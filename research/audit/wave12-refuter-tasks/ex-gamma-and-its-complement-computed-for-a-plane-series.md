## Selection reasons

- critical risk (16): 27 declared dependencies; 27 cited facts; 11 numbered proof steps; biconditional / both-direction claim; existence, choice, uniqueness, or well-definedness; boundary-sensitive language; analytic limiting/completeness language
- top-20 manifest-edge consumer (27 outgoing relationships)
- direct-citation consumer of generated-risk seed rem-rn-conventions-and-scope

## Target item — `ex-gamma-and-its-complement-computed-for-a-plane-series`

Normalized current SHA-256: `be7f47f2e7828b6b69a9713cf222f473cc98fd406da9e6420f3e0fb0cd02b976`

The complete exact-current item follows, including frontmatter:

````markdown
---
id: ex-gamma-and-its-complement-computed-for-a-plane-series
kind: example
title: "A convergent series in $\\mathbb{R}^{2}$ with $\\Gamma$ a line and $\\Gamma^{\\perp}$ a line, computed from the definition"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-generated
deps: [def-the-space-of-summing-directions, def-series-of-vectors-and-rearrangement, thm-rearrangement-sums-lie-in-an-affine-subspace, thm-componentwise-convergence-and-completeness, thm-alternating-series-test, thm-p-series-rational, thm-riemann-series-theorem, lem-series-linearity, lem-alternating-sequence, def-monotone-sequence, def-euclidean-inner-product, def-p-norms-on-rn, def-norm-and-normed-space, def-series, def-absolute-and-conditional-convergence, def-linear-subspace, def-canonical-natural, lem-of-naturals-positive, lem-of-inverse-positive, cor-archimedean-reciprocal, def-integer-power, def-real-limit, lem-of-abs-value, lem-standard-basis-of-f-n, def-injection-surjection-bijection, thm-of-square-roots, def-rational-power]
justified_by: []
aliases: []
landmark: false
proof_strategy: direct
verification:
  precheck: pass
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-28
  audited: 2026-07-29
sources:
  scraped: []
  references:
    - title: "Riemann series theorem (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Riemann_series_theorem"
    - title: "Levy-Steinitz theorem (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/L%C3%A9vy%E2%80%93Steinitz_theorem"
    - title: "T. Banakh, A Simple Inductive Proof of the Levy-Steinitz Theorem"
      url: "https://arxiv.org/abs/1711.04136"
pipeline_run: null
---

## Example

Let $(\varepsilon_k)$ be the alternating sequence, the unique sequence of reals
with $\varepsilon_0 = 1$ and $\varepsilon_{k+1} = -\varepsilon_k$, so
$|\varepsilon_k| = 1$ for every $k$ ([[lem-alternating-sequence]]). In
$\mathbb{R}^{2}$ put

$$x_k \;:=\; \Bigl(\frac{\varepsilon_k}{\iota(k+1)},\ 0\Bigr) \qquad (k \in \mathbb{N}),$$

with $\iota$ the canonical natural ([[def-canonical-natural]]). Call a **line
through the origin** the set of scalar multiples of a fixed nonzero vector; each
such set is a linear subspace ([[def-linear-subspace]]). Then:

1. $\sum x_k$ converges, to $s = (S, 0)$ where $S$ is the sum of the alternating
   harmonic series; **the value of $S$ is not computed here**, being a logarithm
   and outside this page's reach.
2. $\sum x_k$ does **not** converge absolutely
   ([[def-series-of-vectors-and-rearrangement]]).
3. $\Gamma = \{\, (0,t) : t \in \mathbb{R} \,\}$, the line of multiples of $e_1$,
   and $\Gamma^{\perp} = \{\, (t,0) : t \in \mathbb{R} \,\}$, the line of
   multiples of $e_0$ ([[def-the-space-of-summing-directions]]).
4. Consequently [[thm-rearrangement-sums-lie-in-an-affine-subspace]] confines
   every rearrangement sum to the horizontal line
   $s + \Gamma^{\perp} = \{(t,0) : t \in \mathbb{R}\}$; and for **this** series
   the confinement is exact, $\mathcal{S}(x) = s + \Gamma^{\perp}$, by the
   published [[thm-riemann-series-theorem]] applied to the first coordinate.

**Clause 4 decides nothing about the general question.** This series is
degenerate: it lies inside a line, so its rearrangement behaviour is the
one-dimensional behaviour of its first coordinate and nothing more. It is
therefore **not** evidence about whether $\mathcal{S}(x) = s + \Gamma^{\perp}$
for a series genuinely spread over $\mathbb{R}^{n}$ with $n \ge 2$, a question
this library does not settle ([[rem-rn-conventions-and-scope]]).

## Facts & Assumptions

**Given:** The sequence $(x_k)$ above, its first coordinate sequence $c_k := \varepsilon_k/\iota(k+1)$ and the sequence $b_k := 1/\iota(k+1)$.

[L1] The alternating sequence: $\varepsilon_0 = 1$, $\varepsilon_{k+1} = -\varepsilon_k$, and $|\varepsilon_k| = 1$ ([[lem-alternating-sequence]], [[lem-of-abs-value]]).

[L2] $\iota(k+1) > 0$ and $\iota$ is strictly increasing; $0 < u \le v$ gives $0 < 1/v \le 1/u$; and for every real $\varepsilon>0$ there is $K$ with $1/\iota(K+1) < \varepsilon$ ([[def-canonical-natural]], [[lem-of-naturals-positive]], [[lem-of-inverse-positive]], [[cor-archimedean-reciprocal]]).

[L3] The alternating series test: a nonincreasing null sequence $(b_k)$ makes $\sum\varepsilon_k b_k$ converge ([[thm-alternating-series-test]], [[def-monotone-sequence]], [[def-real-limit]], [[def-series]]).

[L4] The $p$-series theorem: $\sum_{k\ge1}1/k^{p}$ converges if and only if $p>1$; at $p=1$ the harmonic series diverges ([[thm-p-series-rational]], [[def-rational-power]], [[def-series]]).

[L5] Convergence in $\mathbb{R}^{2}$ is componentwise ([[thm-componentwise-convergence-and-completeness]] clause 1, [[def-series-of-vectors-and-rearrangement]], [[lem-standard-basis-of-f-n]]).

[L6] The inner product, the Euclidean norm and the definition of $\Gamma$ and $\Gamma^{\perp}$ ([[def-euclidean-inner-product]], [[def-p-norms-on-rn]], [[def-norm-and-normed-space]], [[def-the-space-of-summing-directions]], [[thm-of-square-roots]], [[def-integer-power]]).

[L7] For $c \ne 0$, $\sum c\,a_k$ converges if and only if $\sum a_k$ converges ([[lem-series-linearity]] clause 3).

[L8] The containment theorem ([[thm-rearrangement-sums-lie-in-an-affine-subspace]]) and the Riemann series theorem: a conditionally convergent real series has, for every real $c$, a rearrangement converging to $c$ ([[thm-riemann-series-theorem]] clause 1, [[def-absolute-and-conditional-convergence]], [[def-injection-surjection-bijection]]).

## Verification

**Proof technique:** direct.

1.1 $(b_k)$ is positive, nonincreasing and converges to $0$: positivity and monotonicity from $0 < \iota(k+1) < \iota(k+2)$, and convergence because for a rational $\varepsilon>0$ an index $K$ with $1/\iota(K+1)<\varepsilon$ gives $b_k \le b_K < \varepsilon$ for $k \ge K$. [L2]

1.2 The second coordinate sequence is constantly $0$, so its series converges with sum $0$. [L5]

2.1 By the alternating series test $\sum_k c_k = \sum_k \varepsilon_k b_k$ converges; write $S$ for its sum. [step 1.1, L3]

2.2 $\lVert x_k\rVert_2 = \sqrt{c_k^{2}+0} = |c_k| = |\varepsilon_k| b_k = b_k$, and $\sum_k b_k$ is the harmonic series, which diverges; so $\sum x_k$ does not converge absolutely, which is clause 2. [step 1.1, L1, L4, L6]

3.1 By componentwise convergence, $\sum x_k$ converges with sum $s = (S,0)$, which is clause 1. [step 2.1, step 1.2, L5]

3.2 For $a = (a_0,a_1) \in \mathbb{R}^{2}$: $\langle a, x_k\rangle = a_0 c_k$, so $|\langle a,x_k\rangle| = |a_0|\,b_k$. If $a_0 = 0$ every term is $0$ and the series converges; if $a_0 \ne 0$ then $|a_0| > 0$ and convergence of $\sum_k |a_0| b_k$ would give convergence of $\sum_k b_k$, which is false. [step 2.2, L1, L6, L7]

3.3 Conversely let $t \in \mathbb{R}$. The real series $\sum_k c_k$ converges by step 2.1 and does not converge absolutely by step 2.2, so it converges conditionally, and the Riemann series theorem supplies a bijection $\sigma$ of $\mathbb{N}$ with $\sum_k c_{\sigma(k)} = t$. The rearranged vector series $\sum_k x_{\sigma(k)}$ has first coordinate series $\sum_k c_{\sigma(k)}$ and second coordinate series constantly $0$, so by componentwise convergence it converges to $(t,0)$; hence $(t,0) \in \mathcal{S}(x)$. [step 2.1, step 2.2, L5, L8]

4.1 Hence $\Gamma = \{a : a_0 = 0\} = \{(0,t) : t \in \mathbb{R}\}$, the set of scalar multiples of $e_1$. [step 3.2, L6]

5.1 For $y = (y_0,y_1)$: $y \in \Gamma^{\perp}$ means $\langle (0,t), y\rangle = t\,y_1 = 0$ for every real $t$, which at $t = 1$ forces $y_1 = 0$, and conversely $y_1 = 0$ makes every such product $0$. So $\Gamma^{\perp} = \{(t,0) : t \in \mathbb{R}\}$, the set of scalar multiples of $e_0$, and clause 3 is proved. [step 4.1, L6]

6.1 By the containment theorem, $\mathcal{S}(x) \subseteq s + \Gamma^{\perp} = \{\,(S+t,\ 0) : t \in \mathbb{R}\,\} = \{\,(w,0) : w\in\mathbb{R}\,\}$. [step 3.1, step 5.1, L8]

7.1 Steps 6.1 and 3.3 give $\mathcal{S}(x) = s + \Gamma^{\perp}$, which is clause 4. [step 6.1, step 3.3] ∎

## Remarks

- **Why this example is degenerate, and why that is said out loud.** Every term $x_k$ lies in the line $\Gamma^{\perp}$, so the whole series lives there and its rearrangement theory is the theory of the real series $\sum c_k$. The equality in clause 4 is therefore the published [[thm-riemann-series-theorem]] wearing two coordinates, not a higher-dimensional phenomenon. **Nothing here supports or contradicts any statement about a series whose terms span $\mathbb{R}^{2}$.**

- **The divergence of the harmonic series may be had two ways.** Step 2.2 uses [[thm-p-series-rational]] at $p = 1$; the Cauchy condensation test gives the same conclusion, and either citation would do.

- **What the example makes concrete.** $\Gamma$ is computed from its definition, one direction at a time, and turns out to be the set of directions orthogonal to where the series actually moves: testing against $e_1$ sees only zeros, and testing against $e_0$ sees the alternating harmonic series, which is not absolutely summable. That is exactly the dichotomy [[def-the-space-of-summing-directions]] is built to record.
````

## Wave 12 provenance row

```json
{
  "id": "ex-gamma-and-its-complement-computed-for-a-plane-series",
  "statement": "ai-altered",
  "proof": "ai-generated",
  "evidence": "semantic-source",
  "urls": [
    "https://arxiv.org/abs/1711.04136"
  ],
  "rationale": "A convergent series in $\\\\mathbb{R}^{2}$ with $\\\\Gamma$ a line and $\\\\Gamma^{\\\\perp}$ a line, computed from the definition: The Levy–Steinitz source supplies the finite-dimensional rearrangement-sum affine-subspace framework; the item uses the library’s Gamma/Gamma-perp notation, zero-based series, and either states a weaker containment, computes a specialization, or refutes an overgeneralization. The supplied numbered argument was audited as a local proof rather than a transcription or identifiable adaptation of a source proof.",
  "alpha_concurred": false,
  "at": "2026-08-09"
}
```

## Exact-current proof contract

```json
{
  "citations": [
    {
      "fact": "L1",
      "source": "lem-alternating-sequence",
      "source_section": "Statement",
      "quote": "Let $\\sigma$ be the successor on $\\mathbb{N}$ ([[def-natural-numbers]]). There are functions $e, o : \\mathbb{N} \\to \\mathbb{N}$ and a sequence $(s_k)$ of reals ([[def-sequence]]) with the following properties. 1. **The index maps.** $e$ is the unique function with $e_0 = 0$ and $e_{\\sigma(j)} = \\sigma(\\sigma(e_j))$, and $o$ the unique function with $o_0 = \\sigma(0)$ and $o_{\\sigma(j)} = \\sigma(\\sigma(o_j))$. Both are **strictly increasing**. 2. **The partition.** $\\mathbb{N}$ is the **disjoint union** of the ranges of $e$ and of $o$: every natural number is $e_i$ for exactly one $i$ or $o_i$ for exactly one $i$, and never both. 3. **The alternating sequence.** $(s_k)$ is the **unique** sequence of reals with $$s_0 = 1, \\qquad s_{\\sigma(k)} = -s_k \\quad (k \\in \\mathbb{N}).$$ 4. **Its values.** $|s_k| = 1$ for every $k$, so $(s_k)$ is bounded; and $$s_{e_j} = 1, \\qquad s_{o_j} = -1 \\qquad (j \\in \\mathbb{N}),$$ that is $s \\circ e$ is constantly $1$ and $s \\circ o$ constantly $-1$. This is the sequence usually written $s_k = (-1)^k$, with $e_j = 2j$ and $o_j = 2j+1$, presented by the recursions that its proofs actually use. It is collected here once because three separate items on this page and its companion need an alternating or interleaved witness, and rebuilding the recursion inside each of them is what this lemma exists to prevent.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.2",
        "3.2"
      ]
    },
    {
      "fact": "L1",
      "source": "lem-of-abs-value",
      "source_section": "Statement",
      "quote": "Let $F$ be an ordered field ([[def-ordered-field]]) and let $x, y \\in F$, with $|x|$ the absolute value ([[def-abs-value]]). Then $$|x| \\ge 0; \\quad |x| = 0 \\iff x = 0; \\quad -|x| \\le x \\le |x|; \\quad |-x| = |x|; \\quad |xy| = |x|\\,|y|;$$ and, for every $c > 0$, one has $|x| < c \\iff -c < x < c$.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.2",
        "3.2"
      ]
    },
    {
      "fact": "L2",
      "source": "def-canonical-natural",
      "source_section": "Definition",
      "quote": "Let $F$ be a field ([[def-field]]) with additive identity $0_F$ and multiplicative identity $1_F$. Define $\\iota : \\mathbb{N} \\to F$ by recursion on $\\mathbb{N}$ ([[def-natural-numbers]], [[thm-recursion]]): $$\\iota(0) \\;:=\\; 0_F, \\qquad \\iota(n+1) \\;:=\\; \\iota(n) + 1_F .$$ $\\iota(n)$ is the **canonical natural** of $n$ in $F$. It is also written $n \\cdot 1_F$, and for $n \\ge 1$ it is $1_F$ added to itself $n$ times. **Why the notation is needed at all.** A natural number in this library is a von Neumann natural, that is a set ([[def-natural-numbers]]), and a set is not an element of $F$. So $1/n$, $n^{\\alpha}$ and $x/n$ are not expressions of $F$ when $n$ is a natural: what they mean is $1/\\iota(n)$, $\\iota(n)^{\\alpha}$ and $x/\\iota(n)$. The map $\\iota$ is what carries a counting number into the field, and writing it is the whole reason a reader meets $1/\\iota(k+1)$ where an informal text would write $1/(k+1)$.",
      "quote_selection": "full-source-section",
      "uses": [
        "1.1"
      ]
    },
    {
      "fact": "L2",
      "source": "lem-of-naturals-positive",
      "source_section": "Statement",
      "quote": "Let $F$ be an ordered field, with field structure as in [[def-field]], and for $n \\ge 1$ let $n \\cdot 1_F$ denote the canonical natural number $\\underbrace{1_F + \\cdots + 1_F}_{n}$, defined recursively by $1 \\cdot 1_F = 1_F$ and $(n+1) \\cdot 1_F = n \\cdot 1_F + 1_F$. Then for every $n \\ge 1$: - $n \\cdot 1_F > 0$ and $(n+1) \\cdot 1_F > n \\cdot 1_F$; - the map $n \\mapsto n \\cdot 1_F$ is strictly increasing, hence injective, on $\\{1, 2, 3, \\dots\\}$; - $(m+n) \\cdot 1_F = m \\cdot 1_F + n \\cdot 1_F$ and $(mn) \\cdot 1_F = (m \\cdot 1_F)(n \\cdot 1_F)$ for all $m, n \\ge 1$.",
      "quote_selection": "full-source-section",
      "uses": [
        "1.1"
      ]
    },
    {
      "fact": "L2",
      "source": "lem-of-inverse-positive",
      "source_section": "Statement",
      "quote": "Let $F$ be an ordered field ([[def-ordered-field]]) with positive cone $P$, and let $a, b \\in F$. 1. If $a > 0$ then $a^{-1} > 0$. 2. If $0 < a < b$ then $0 < b^{-1} < a^{-1}$.",
      "quote_selection": "full-source-section",
      "uses": [
        "1.1"
      ]
    },
    {
      "fact": "L2",
      "source": "cor-archimedean-reciprocal",
      "source_section": "Statement",
      "quote": "Let $F$ be a complete ordered field ([[def-complete-ordered-field]]) and let $\\varepsilon \\in F$ with $\\varepsilon > 0$. Then there is a natural number $n \\ge 1$ such that $$\\frac{1}{n \\cdot 1_F} < \\varepsilon ,$$ where $n \\cdot 1_F$ is the canonical natural of $F$ ([[thm-of-archimedean]]) and $1/(n \\cdot 1_F)$ is its multiplicative inverse ([[def-field]]). As is standard we abbreviate $n \\cdot 1_F$ to $n$ and write the conclusion $1/n < \\varepsilon$. This is the **reciprocal form** of the Archimedean property. [[thm-of-archimedean]] on its own delivers only the assertion that the canonical naturals are cofinal, $x < n \\cdot 1_F$; the form actually used in analysis, that the reciprocals of the naturals get below every positive bound, is the statement above, and it is recorded separately so that no proof has to reconstruct the inversion step in passing.",
      "quote_selection": "full-source-section",
      "uses": [
        "1.1"
      ]
    },
    {
      "fact": "L3",
      "source": "thm-alternating-series-test",
      "source_section": "Statement",
      "quote": "Let $(\\varepsilon_k)$ be the alternating sequence of [[lem-alternating-sequence]], that is the unique sequence of reals with $\\varepsilon_0 = 1$ and $\\varepsilon_{k+1} = -\\varepsilon_k$, which is what is usually written $\\varepsilon_k = (-1)^k$; let $e$ and $o$ be its even and odd index maps, so that $\\varepsilon_{e_j} = 1$, $\\varepsilon_{o_j} = -1$, and every natural number is $e_j$ for exactly one $j$ or $o_j$ for exactly one $j$. Let $(b_k)$ be a sequence of reals that is nonincreasing ([[def-monotone-sequence]]) and converges to $0$ ([[def-real-limit]]); then $b_k \\ge 0$ for every $k$. Write $t_n := \\sum_{k<n} \\varepsilon_k b_k$ for the partial sums ([[def-series]]). Then: 1. the series $\\sum \\varepsilon_k b_k$ converges; write $L$ for its sum; 2. $t_{e_j} \\le L \\le t_{o_j}$ for every $j \\in \\mathbb{N}$, and for every $n \\in \\mathbb{N}$ the sum $L$ lies between the two consecutive partial sums $t_n$ and $t_{n+1}$; 3. $|L - t_n| \\le b_n$ for every $n \\in \\mathbb{N}$. Claim 3 is the error bound: the partial sum $t_n$, which uses the $n$ terms $\\varepsilon_0 b_0, \\dots, \\varepsilon_{n-1}b_{n-1}$, differs from the sum by at most the first term omitted. **Only claim 1 is a corollary of [[thm-dirichlet-test]].** Claims 2 and 3 are not: they come from the interlacing of the even-index and odd-index partial sums, and that argument is carried out below rather than smuggled into the Dirichlet estimate, which produces no bracketing at all.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.1"
      ]
    },
    {
      "fact": "L3",
      "source": "def-monotone-sequence",
      "source_section": "Definition",
      "quote": "Let $(x_k)$ be a sequence of reals ([[def-sequence]]), with $\\mathbb{R}$ ordered as in [[def-real-order]] and [[def-complete-ordered-field]], and with $\\mathbb{N}$ ordered as in [[def-nat-order]]. The sequence is: - **nondecreasing** when $x_j \\le x_k$ for all $j \\le k$; - **increasing** (or *strictly increasing*) when $x_j < x_k$ for all $j < k$; - **nonincreasing** when $x_j \\ge x_k$ for all $j \\le k$; - **decreasing** (or *strictly decreasing*) when $x_j > x_k$ for all $j < k$; - **monotone** when it is nondecreasing or nonincreasing; - **strictly monotone** when it is increasing or decreasing; - **eventually monotone** when some tail $x^{(K)}$ ([[def-sequence]]) is monotone, that is when there is $K \\in \\mathbb{N}$ such that the restriction of the comparison to indices $\\ge K$ is one-signed. An increasing sequence is nondecreasing and a decreasing sequence is nonincreasing, since $j \\le k$ means $j < k$ or $j = k$ and the second case gives equality. A sequence that is both nondecreasing and nonincreasing is constant. **Consecutive comparisons suffice, and that is an induction.** The four conditions above quantify over *all* pairs of indices, but what one checks in practice, and what a recursive construction delivers, is the comparison of consecutive terms. The two agree: > $(x_k)$ is nondecreasing **if and only if** $x_k \\le x_{\\sigma(k)}$ for every > $k \\in \\mathbb{N}$, and $(x_k)$ is increasing **if and only if** > $x_k < x_{\\sigma(k)}$ for every $k \\in \\mathbb{N}$; likewise, with the > inequalities reversed, for nonincreasing and decreasing. The forward implications are the instances $j = k$, $k = \\sigma(k)$ of the definitions, using $k < \\sigma(k)$ ([[lem-nat-discrete]]). For the converse, suppose $x_i \\le x_{\\sigma(i)}$ for every $i$ and fix $k$; we show by induction on $k$ ([[thm-induction-principle]]) that $x_j \\le x_k$ for every $j \\le k$. For $k = 0$: $j \\le 0$ forces $j = 0$, and $x_0 \\le x_0$. Assume the statement for $k$ and let $j \\le \\sigma(k)$. If $j = \\sigma(k)$ then $x_j \\le x_{\\sigma(k)}$ by reflexivity. Otherwise $j < \\sigma(k)$, and then $j \\le k$: were $k < j$ we would have $k < j < \\sigma(k)$, which [[lem-nat-discrete]] excludes, so $j \\le k$ by totality of the order on $\\mathbb{N}$ ([[thm-nat-linear-order]]). The induction hypothesis gives $x_j \\le x_k$, and $x_k \\le x_{\\sigma(k)}$ by assumption, so $x_j \\le x_{\\sigma(k)}$ by transitivity. This completes the induction. The three remaining equivalences are the same argument with $\\le$ replaced by $<$, $\\ge$ or $>$, transitivity of the strict order being used in the same place. **Boundedness of a monotone sequence is one-sided.** A nondecreasing sequence is bounded below by its first term $x_0$, and a nonincreasing sequence is bounded above by $x_0$, both immediately from the definition with $j = 0$. So for a nondecreasing sequence the only substantive question is whether it is bounded above, and for a nonincreasing sequence whether it is bounded below. The range of $(x_k)$ is the set $\\{x_k : k \\in \\mathbb{N}\\}$ ([[def-sequence]]), and it is bounded above, bounded below or bounded in the sense of [[def-bounded-set]] exactly when the sequence is.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.1"
      ]
    },
    {
      "fact": "L3",
      "source": "def-real-limit",
      "source_section": "Definition",
      "quote": "A sequence $(x_k)$ of reals **converges** to $x \\in \\mathbb{R}$ when for every rational $\\varepsilon > 0$ there is $K$ with $|x_k - x| < \\hat\\varepsilon$ for all $k \\ge K$. It is **Cauchy** when for every rational $\\varepsilon > 0$ there is $K$ with $|x_k - x_l| < \\hat\\varepsilon$ for all $k, l \\ge K$.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.1"
      ]
    },
    {
      "fact": "L3",
      "source": "def-series",
      "source_section": "Definition",
      "quote": "Throughout, $\\mathbb{R}$ is the complete ordered field ([[def-real-numbers]]) and a **sequence of reals** is a function $a : \\mathbb{N} \\to \\mathbb{R}$ ([[def-sequence]]), written $(a_k)$; recall that $\\mathbb{N}$ contains $0$. **Partial sums.** Let $(a_k)$ be a sequence of reals. Its **sequence of partial sums** is $$s_n \\;:=\\; \\sum_{k < n} a_k \\qquad (n \\in \\mathbb{N}),$$ the finite sum of [[def-finite-sum]]. In particular $s_0 = 0$, the empty sum, and $s_{n+1} = s_n + a_n$ for every $n$, those being exactly the two recursion clauses that define the finite sum. Note that $s_n$ is the sum of the $n$ terms $a_0, \\dots, a_{n-1}$, so the index $n$ counts terms rather than naming the last one. **Convergence, the sum, divergence.** The **series** of $(a_k)$, written $\\sum a_k$, **converges** when the sequence $(s_n)$ of partial sums converges ([[def-real-limit]]), and then the **sum of the series** is $$\\sum_{k=0}^{\\infty} a_k \\;:=\\; \\lim_{n} s_n .$$ The series **diverges** when $(s_n)$ does not converge. A convergent sequence of reals has exactly one limit ([[lem-limit-unique]]), so the displayed symbol names a single real number and nothing further has to be checked for it to be well defined. **Series with a general starting index.** Let $m \\in \\mathbb{N}$ and let $a$ be a function on $\\{\\, k \\in \\mathbb{N} : k \\ge m \\,\\}$, which we call a **family from $m$** and write $(a_k)_{k \\ge m}$. The series $$\\sum_{k \\ge m} a_k$$ is by definition the series of the sequence $b_j := a_{j + m}$, $j \\in \\mathbb{N}$, which is a genuine sequence of reals; it converges exactly when that series converges, and its sum is then written $\\sum_{k = m}^{\\infty} a_k$. Its partial sums are $$\\sum_{k=m}^{n-1} a_k \\;=\\; \\sum_{j < n-m} a_{m+j} \\qquad (n \\ge m),$$ in the notation of [[def-finite-sum]], the value at $n = m$ being the empty sum $0$. A sequence on $\\mathbb{N}$ is the case $m = 0$, and the two readings of $\\sum a_k$ agree there, since $b_j = a_j$. **This clause is not a convenience.** Sequences in this library are functions on $\\mathbb{N}$ and $\\mathbb{N}$ contains $0$ ([[def-sequence]]), while many of the classical series are built from expressions that are undefined at the index $0$: $1/k$, $1/k^{p}$ and $|a_k|^{1/k}$ all require $k \\ge 1$. Writing such a series as $\\sum_{k \\ge 1} a_k$ names an honest object, whereas writing it as a sequence on $\\mathbb{N}$ would require a value at an index where the defining expression has none. Every statement on this page says which starting index it uses. **Tail series.** For $N \\in \\mathbb{N}$, the **$N$-th tail series** of $\\sum a_k$ is $\\sum_{k \\ge N} a_k$, that is the series of the $N$-th tail $a^{(N)}$ of [[def-sequence]], whose terms are $a^{(N)}_j = a_{j+N}$. The $0$-th tail series is the series itself.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.1"
      ]
    },
    {
      "fact": "L4",
      "source": "thm-p-series-rational",
      "source_section": "Statement",
      "quote": "Let $p \\in \\mathbb{Q}$ with $p > 0$. For a natural number $k \\ge 1$ write $\\iota(k) = k \\cdot 1_{\\mathbb{R}}$ for the canonical natural, which is positive ([[lem-of-naturals-positive]]), and write $k^{p} := \\iota(k)^{p}$ for its rational power ([[def-rational-power]]). Then $$\\sum_{k \\ge 1} \\frac{1}{k^{p}} \\ \\text{converges} \\qquad \\Longleftrightarrow \\qquad p > 1 .$$ In particular the harmonic series $\\sum_{k \\ge 1} 1/k$ diverges, at $p = 1$, and $\\sum_{k \\ge 1} 1/k^{2}$ converges, at $p = 2$. **The index range is not cosmetic.** The series starts at $k = 1$ because $1/0^{p}$ is undefined: [[def-rational-power]] gives $0^{p} = 0$ for rational $p > 0$, and $0$ has no inverse. Sequences here are functions on $\\mathbb{N}$ and $\\mathbb{N}$ contains $0$ ([[def-series]]), so the object named above is a series from the starting index $1$ in the sense of [[def-series]], not a series of a sequence on $\\mathbb{N}$. **The exponent is rational, and that is a limitation of this page.** Rational powers of a positive base are what [[def-rational-power]] supplies; real exponents require the exponential and the logarithm, which this library develops later. The statement above is therefore the full $p$-series theorem for every exponent this page can name.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.2"
      ]
    },
    {
      "fact": "L4",
      "source": "def-rational-power",
      "source_section": "Definition",
      "quote": "Let $a \\in \\mathbb{R}$ with $a > 0$ and let $r \\in \\mathbb{Q}$ ([[def-rationals]]). Every rational has a representative with positive denominator ([[lem-rat-positive-denominator]]), so write $r = m/n$ with $m \\in \\mathbb{Z}$ and $n$ a positive integer; a positive integer is the image of a unique natural $\\ge 1$ ([[lem-nat-embeds-int]]), and we write $n$ for that natural too. Define $$a^{r} := \\big(a^{1/n}\\big)^{m},$$ where $a^{1/n}$ is the unique nonnegative $n$-th root of $a$ ([[thm-nth-roots-exist]]) and the outer exponent is an integer power ([[def-integer-power]]). The outer power is legitimate because $a^{1/n} > 0$ when $a > 0$, so it has an inverse and negative integer exponents are allowed. **Well-definedness.** The right-hand side must not depend on which representative $m/n$ of $r$ was chosen. It does not: that is [[lem-rational-power-well-defined]], which is recorded in this item's `justified_by` rather than in its `deps`, since it is a statement *about* the operation defined here and therefore depends on this definition. **The base must be positive.** For $a < 0$ the same formula is not a definition at all, because different representatives of the same rational give different answers, or no answer: see [[fs-rational-power-of-negative-base]], which is exactly the item that justifies the restriction. **Supplementary clause for the base $0$.** For $a = 0$ and rational $r > 0$ ([[def-rat-order]]) the displayed formula still makes sense and still does not depend on the representative: $r > 0$ forces $m \\ge 1$, and $\\big(0^{1/n}\\big)^{m} = 0^{m} = 0$ ([[thm-nth-roots-exist]] applies to every $a \\ge 0$). So we set $0^{r} = 0$ for rational $r > 0$. For $r < 0$ the expression $0^{r}$ is left undefined, since $0$ has no inverse. This clause is what lets the inequalities later on this page be stated for nonnegative entries rather than for positive ones only.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.2"
      ]
    },
    {
      "fact": "L4",
      "source": "def-series",
      "source_section": "Definition",
      "quote": "Throughout, $\\mathbb{R}$ is the complete ordered field ([[def-real-numbers]]) and a **sequence of reals** is a function $a : \\mathbb{N} \\to \\mathbb{R}$ ([[def-sequence]]), written $(a_k)$; recall that $\\mathbb{N}$ contains $0$. **Partial sums.** Let $(a_k)$ be a sequence of reals. Its **sequence of partial sums** is $$s_n \\;:=\\; \\sum_{k < n} a_k \\qquad (n \\in \\mathbb{N}),$$ the finite sum of [[def-finite-sum]]. In particular $s_0 = 0$, the empty sum, and $s_{n+1} = s_n + a_n$ for every $n$, those being exactly the two recursion clauses that define the finite sum. Note that $s_n$ is the sum of the $n$ terms $a_0, \\dots, a_{n-1}$, so the index $n$ counts terms rather than naming the last one. **Convergence, the sum, divergence.** The **series** of $(a_k)$, written $\\sum a_k$, **converges** when the sequence $(s_n)$ of partial sums converges ([[def-real-limit]]), and then the **sum of the series** is $$\\sum_{k=0}^{\\infty} a_k \\;:=\\; \\lim_{n} s_n .$$ The series **diverges** when $(s_n)$ does not converge. A convergent sequence of reals has exactly one limit ([[lem-limit-unique]]), so the displayed symbol names a single real number and nothing further has to be checked for it to be well defined. **Series with a general starting index.** Let $m \\in \\mathbb{N}$ and let $a$ be a function on $\\{\\, k \\in \\mathbb{N} : k \\ge m \\,\\}$, which we call a **family from $m$** and write $(a_k)_{k \\ge m}$. The series $$\\sum_{k \\ge m} a_k$$ is by definition the series of the sequence $b_j := a_{j + m}$, $j \\in \\mathbb{N}$, which is a genuine sequence of reals; it converges exactly when that series converges, and its sum is then written $\\sum_{k = m}^{\\infty} a_k$. Its partial sums are $$\\sum_{k=m}^{n-1} a_k \\;=\\; \\sum_{j < n-m} a_{m+j} \\qquad (n \\ge m),$$ in the notation of [[def-finite-sum]], the value at $n = m$ being the empty sum $0$. A sequence on $\\mathbb{N}$ is the case $m = 0$, and the two readings of $\\sum a_k$ agree there, since $b_j = a_j$. **This clause is not a convenience.** Sequences in this library are functions on $\\mathbb{N}$ and $\\mathbb{N}$ contains $0$ ([[def-sequence]]), while many of the classical series are built from expressions that are undefined at the index $0$: $1/k$, $1/k^{p}$ and $|a_k|^{1/k}$ all require $k \\ge 1$. Writing such a series as $\\sum_{k \\ge 1} a_k$ names an honest object, whereas writing it as a sequence on $\\mathbb{N}$ would require a value at an index where the defining expression has none. Every statement on this page says which starting index it uses. **Tail series.** For $N \\in \\mathbb{N}$, the **$N$-th tail series** of $\\sum a_k$ is $\\sum_{k \\ge N} a_k$, that is the series of the $N$-th tail $a^{(N)}$ of [[def-sequence]], whose terms are $a^{(N)}_j = a_{j+N}$. The $0$-th tail series is the series itself.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.2"
      ]
    },
    {
      "fact": "L5",
      "source": "thm-componentwise-convergence-and-completeness",
      "source_section": "Statement",
      "quote": "Let $n \\in \\mathbb{N}$ with $n \\ge 1$, let $\\mathbb{R}^{n}$ carry the Euclidean metric $d_2$ of [[lem-metrics-on-rn]], and let $\\bigl(x^{(j)}\\bigr)_{j\\in\\mathbb{N}}$ be a sequence in $\\mathbb{R}^{n}$ ([[def-metric-convergence]]). For $k < n$ write $\\bigl(x^{(j)}_k\\bigr)_{j\\in\\mathbb{N}}$ for the $k$-th **coordinate sequence**, a sequence of reals ([[def-sequence]]). Then: 1. **Convergence is componentwise.** For $x \\in \\mathbb{R}^{n}$, $x^{(j)} \\to x$ in $(\\mathbb{R}^{n}, d_2)$ if and only if $x^{(j)}_k \\to x_k$ in $\\mathbb{R}$ for every $k<n$ ([[def-real-limit]]). 2. **Cauchyness is componentwise.** $\\bigl(x^{(j)}\\bigr)$ is Cauchy in $(\\mathbb{R}^{n},d_2)$ ([[def-cauchy-in-metric]]) if and only if every coordinate sequence is Cauchy in $\\mathbb{R}$. 3. **Completeness in every norm.** For every norm $N$ on $\\mathbb{R}^{n}$ ([[def-norm-and-normed-space]]) the metric space $(\\mathbb{R}^{n}, d_N)$ is complete ([[def-complete-metric-space]]). **Clause 3 is obtained by citation and is not reproved here.** [[thm-euclidean-space-complete]] clause 2 states that $(\\mathbb{R}^{n},d_2)$ is complete, **for $n \\ge 1$ only**, and this theorem carries that hypothesis forward without weakening it; what is added is the passage from $d_2$ to an arbitrary norm, through [[thm-all-norms-on-rn-are-equivalent]] and the dictionary of [[def-equivalent-norms]].",
      "quote_selection": "full-source-section",
      "uses": [
        "1.2",
        "3.1",
        "3.3"
      ]
    },
    {
      "fact": "L5",
      "source": "def-series-of-vectors-and-rearrangement",
      "source_section": "Definition",
      "quote": "Let $n \\in \\mathbb{N}$ with $n \\ge 1$, so that $\\mathbb{R}^{n}$ carries the Euclidean metric $d_2$ ([[lem-metrics-on-rn]], [[lem-p-norms-are-norms-and-induce-the-published-metrics]]). A **sequence of vectors** is a function $x : \\mathbb{N} \\to \\mathbb{R}^{n}$, written $(x_k)$ with $x_k := x(k)$; as everywhere in this library $\\mathbb{N}$ contains $0$ and a sequence is indexed from $0$ ([[def-sequence]], [[def-metric-convergence]]). ### Partial sums and convergence The **partial sums** of $(x_k)$ are $$s_N \\;:=\\; \\sum_{k<N} x_k \\;\\in\\; \\mathbb{R}^{n} \\qquad (N \\in \\mathbb{N}),$$ the finite sum of the vector space $\\mathbb{R}^{n}$ ([[def-linear-combination-and-span]]), so $s_0 = 0$ and $s_{N+1} = s_N + x_N$. **No third notion of finite sum is introduced**: by [[lem-standard-basis-of-f-n]] clause 1 the vector sum is computed pointwise, $(s_N)(j) = \\sum_{k<N} x_k(j)$ for $j<n$, the right-hand side being the real finite sum of [[def-finite-sum]]. The **series** $\\sum x_k$ **converges to $s \\in \\mathbb{R}^{n}$** when $s_N \\to s$ in $(\\mathbb{R}^{n}, d_2)$ ([[def-metric-convergence]]), and then $s$ is **the sum**, written $\\sum_{k=0}^{\\infty}x_k$. The symbol denotes a single vector, because a sequence in a metric space has at most one limit ([[lem-metric-limits-unique]]). The series **diverges** when $(s_N)$ does not converge. ### Absolute convergence $\\sum x_k$ **converges absolutely** when the real series $\\sum \\lVert x_k\\rVert_2$ converges ([[def-series]]); since $\\lVert x_k\\rVert_2 \\ge 0$ ([[def-norm-and-normed-space]]), this is a statement about a series of nonnegative terms, exactly as in [[def-absolute-and-conditional-convergence]]. **The choice of norm is immaterial.** If $N$ is any norm on $\\mathbb{R}^{n}$ then $c\\lVert x_k\\rVert_2 \\le N(x_k) \\le C\\lVert x_k\\rVert_2$ for fixed $c, C > 0$ ([[thm-all-norms-on-rn-are-equivalent]], [[def-equivalent-norms]]), so $\\sum N(x_k)$ converges exactly when $\\sum\\lVert x_k\\rVert_2$ does, both being series of nonnegative terms. The notion defined above therefore depends on $\\mathbb{R}^{n}$ and not on the norm chosen to test it. ### Rearrangement and the set of rearrangement sums Let $\\sigma : \\mathbb{N} \\to \\mathbb{N}$ be a bijection ([[def-injection-surjection-bijection]]). The **rearrangement of $\\sum x_k$ along $\\sigma$** is the series $\\sum x_{\\sigma(k)}$ of the sequence $k \\mapsto x_{\\sigma(k)}$, verbatim as in [[def-rearrangement-and-unconditional-convergence]] one dimension down. The **set of rearrangement sums** of $(x_k)$ is $$\\mathcal{S}(x) \\;:=\\; \\Bigl\\{\\, s \\in \\mathbb{R}^{n} \\;:\\; \\text{some rearrangement of } \\sum x_k \\text{ converges to } s \\,\\Bigr\\}.$$ Taking $\\sigma$ to be the identity shows that a convergent $\\sum x_k$ has its own sum in $\\mathcal{S}(x)$, so $\\mathcal{S}(x) \\ne \\varnothing$ for a convergent series. ### Agreement with the one-dimensional theory $\\mathbb{R}^{1}$ is the set of functions $1 \\to \\mathbb{R}$ and is **not literally** $\\mathbb{R}$. The map $\\theta : \\mathbb{R} \\to \\mathbb{R}^{1}$ sending $t$ to the function with value $t$ at $0$ is a bijection; it preserves addition and scalar multiplication, since both are computed pointwise ([[def-vector-space]], [[lem-standard-basis-of-f-n]]), and $d_2(\\theta(s),\\theta(t)) = |s-t|$, so it is an isometric bijection ([[def-isometry-and-metric-embedding]]). Under that identification, and for $n = 1$: - the partial sums above are the partial sums of [[def-series]]; - convergence and the sum are those of [[def-series]]; - absolute convergence is that of [[def-absolute-and-conditional-convergence]], since $\\lVert\\theta(t)\\rVert_2 = |t|$; - rearrangement is that of [[def-rearrangement-and-unconditional-convergence]]; - $\\mathcal{S}(x)$ is the image under $\\theta$ of the set of rearrangement sums that the published remark [[rem-rearrangement-in-higher-dimensions]] writes $\\mathcal{S}(a)$. **Every comparison on this page between $\\mathbb{R}^{n}$ and the published one-dimensional theory goes through this identification, and it is stated each time.**",
      "quote_selection": "full-source-section",
      "uses": [
        "1.2",
        "3.1",
        "3.3"
      ]
    },
    {
      "fact": "L5",
      "source": "lem-standard-basis-of-f-n",
      "source_section": "Statement",
      "quote": "Let $F$ be a field ([[def-field]]), let $n \\in \\mathbb{N}$ and let $F^{n}$ be the function space on the von Neumann natural $n = \\{0, \\dots, n-1\\}$, with the pointwise operations ([[def-function-space]], [[def-natural-numbers]], [[lem-nat-order-is-membership]]). For $i < n$ define the **standard unit vector** $e_i \\in F^{n}$ by $$e_i(i) = 1_F, \\qquad e_i(j) = 0_F \\ \\text{ for } j < n \\text{ with } j \\ne i .$$ Then: 1. **Finite sums in a function space are pointwise.** For every set $X$, every $p \\in \\mathbb{N}$, every list $u : p \\to F^{X}$ and every $j \\in X$, $$\\Bigl(\\sum_{k<p} u_k\\Bigr)(j) \\;=\\; \\sum_{k<p} u_k(j),$$ the right-hand sum being taken in $(F,+,0_F)$. (Stated here for an arbitrary $X$ because the companion page needs it at $X = \\mathbb{N}$.) 2. $e : n \\to F^{n}$ is an ordered basis of $F^{n}$ ([[def-linear-basis]]); in particular $e$ is injective and its image $e[n] = \\{\\, e_i : i < n \\,\\}$ is a basis of $F^{n}$ with $e[n] \\approx n$ ([[def-equinumerous]]); 3. for every $\\lambda : n \\to F$ and every $j < n$, $\\bigl(\\sum_{i<n}\\lambda_i e_i\\bigr)(j) = \\lambda_j$; equivalently the coordinate list of $x \\in F^{n}$ with respect to the ordered basis $e$ ([[thm-unique-coordinates-with-respect-to-an-ordered-basis]]) is $i \\mapsto x(i)$; 4. $F^{n}$ is finite-dimensional over $F$ with $\\dim_F F^{n} = n$ ([[def-dimension]]); 5. at $n = 0$ this reads: $F^{0}$ has exactly one element, the empty function, so $F^{0}$ is the zero space, the empty list is its ordered basis, $\\varnothing$ is its basis and $\\dim_F F^{0} = 0$. Every index runs from $0$, so the coordinates of an element of $F^{n}$ are $x_0, \\dots, x_{n-1}$ and no statement above is restricted to $n \\ge 1$.",
      "quote_selection": "full-source-section",
      "uses": [
        "1.2",
        "3.1",
        "3.3"
      ]
    },
    {
      "fact": "L6",
      "source": "def-euclidean-inner-product",
      "source_section": "Definition",
      "quote": "Let $n \\in \\mathbb{N}$. A natural number is a von Neumann natural, that is a set, and $n = \\{0, 1, \\dots, n-1\\}$ ([[def-natural-numbers]], [[lem-nat-order-is-membership]]), so $$\\mathbb{R}^{n} \\;=\\; \\{\\, x \\;:\\; x \\text{ is a function } n \\to \\mathbb{R} \\,\\}$$ is the function space of [[def-function-space]] at $F = \\mathbb{R}$ and $X = n$, a vector space over $\\mathbb{R}$ under the pointwise operations ([[def-vector-space]]). We write $x_k := x(k)$ for $k < n$, and two elements of $\\mathbb{R}^{n}$ are equal exactly when they agree at every $k < n$. This is the same set that [[lem-metrics-on-rn]] calls $\\mathbb{R}^{n}$. The **Euclidean inner product** of $x, y \\in \\mathbb{R}^{n}$ is the real number $$\\langle x, y\\rangle \\;:=\\; \\sum_{k<n} x_k\\,y_k ,$$ the finite sum of [[def-finite-sum]] applied to the list $k \\mapsto x_k y_k$ (extended by $0$ beyond $n$, as every finite list in this library is). The **Euclidean norm** of $x$ is $$\\lVert x\\rVert_2 \\;:=\\; \\sqrt{\\langle x, x\\rangle},$$ which is defined because $\\langle x,x\\rangle = \\sum_{k<n} x_k^{2} \\ge 0$ (a sum of nonnegative terms, [[lem-finite-sum-laws]] clause 4 and [[lem-of-square-positive]], the case $x_k = 0$ giving $x_k^2 = 0$ by [[def-integer-power]]) and every nonnegative real has a unique nonnegative square root ([[thm-of-square-roots]]). ### Both are defined for every $n$, including $n = 0$ At $n = 0$ the set $\\mathbb{R}^{0}$ has exactly one element, the empty function, and it is the zero vector space ([[lem-standard-basis-of-f-n]] clause 5); the sum above is the empty sum, so $\\langle x,y\\rangle = 0$ and $\\lVert x\\rVert_2 = 0$. **This is the first place on this page where the two index regimes diverge, and the divergence is deliberate.** The published metrics $d_1$, $d_2$, $d_\\infty$ of [[lem-metrics-on-rn]] are defined only for $n \\ge 1$, because $d_\\infty$ would otherwise be a maximum over the empty index set; the algebra above needs no such restriction. The boundary in this page runs between the algebra and the metric, not where a reader would guess, and [[rem-rn-conventions-and-scope]] lists exactly which items inherit $n \\ge 1$. ### The algebra of the inner product For all $x, y, z \\in \\mathbb{R}^{n}$ and $\\lambda \\in \\mathbb{R}$: 1. **Symmetry.** $\\langle x,y\\rangle = \\langle y,x\\rangle$, since $x_ky_k = y_kx_k$ termwise. 2. **Additivity in the first argument.** $\\langle x + y, z\\rangle = \\langle x,z\\rangle + \\langle y,z\\rangle$: the list $k \\mapsto (x_k+y_k)z_k$ is the termwise sum of $k \\mapsto x_kz_k$ and $k \\mapsto y_kz_k$, so [[lem-finite-sum-laws]] clause 1 applies. 3. **Homogeneity in the first argument.** $\\langle \\lambda x, y\\rangle = \\lambda\\langle x,y\\rangle$, by [[lem-finite-sum-laws]] clause 2. 4. **Bilinearity.** Clauses 2 and 3 together with symmetry give the same two laws in the second argument. 5. **Positive definiteness.** $\\langle x,x\\rangle \\ge 0$, and $\\langle x,x\\rangle = 0$ if and only if $x = 0$. Indeed a vanishing sum of nonnegative terms has every term $0$ ([[lem-finite-sum-laws]] clause 4), so $x_k^{2} = 0$ for every $k < n$, and a nonzero real has a positive square ([[lem-of-square-positive]]), whence $x_k = 0$ for every $k < n$ and $x = 0$. 6. **Agreement with the published Euclidean metric.** For $n \\ge 1$ and $x, y \\in \\mathbb{R}^{n}$, $\\lVert x - y\\rVert_2 = \\sqrt{\\sum_{k<n}(x_k-y_k)^{2}} = d_2(x,y)$, the two sides being the same expression ([[lem-metrics-on-rn]]). In particular $\\lVert x\\rVert_2 = d_2(x, 0)$. That $\\lVert\\cdot\\rVert_2$ is a norm in the sense of [[def-norm-and-normed-space]] is proved in [[thm-cauchy-schwarz-and-the-euclidean-norm]], where the triangle inequality is obtained from the Cauchy-Schwarz inequality; it is not assumed here.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.2",
        "3.2",
        "4.1",
        "5.1"
      ]
    },
    {
      "fact": "L6",
      "source": "def-p-norms-on-rn",
      "source_section": "Definition",
      "quote": "Let $n \\in \\mathbb{N}$ and let $\\mathbb{R}^{n}$ be the function space of [[def-euclidean-inner-product]], with $x_k := x(k)$ for $k < n$. ### The $p$-norm, for a rational exponent $p \\ge 1$ Let $p \\in \\mathbb{Q}$ with $p \\ge 1$. For $x \\in \\mathbb{R}^{n}$ put $$\\lVert x\\rVert_p \\;:=\\; \\Bigl(\\sum_{k<n} |x_k|^{p}\\Bigr)^{1/p},$$ where $|\\cdot|$ is the absolute value ([[def-abs-value]]), the sum is the finite sum of [[def-finite-sum]], and both powers are the **rational** powers of [[def-rational-power]]. **Every power written here is defined.** Each base $|x_k|$ is a nonnegative real and $p > 0$, so $|x_k|^{p}$ is given by [[def-rational-power]] for $|x_k| > 0$ and by its supplementary clause $0^{p} = 0$ for $|x_k| = 0$; the sum of these nonnegative terms is nonnegative ([[lem-finite-sum-laws]] clause 4), and $1/p$ is a positive rational, so the outer power is defined for the same two reasons. The value does not depend on which representative of $p$ or of $1/p$ is used ([[lem-rational-power-well-defined]]). **The exponent is a rational, and that is not a matter of taste.** [[def-rational-power]] supplies $a^{r}$ for a nonnegative base and a **rational** exponent only; real exponents do not exist at this point in the reading order, and [[rem-real-exponents-deferred]] records exactly why. This is also why the published Minkowski inequality [[thm-minkowski-finite]], which is what makes the triangle inequality work below, is itself stated for rational $p \\ge 1$. **No statement on this page is written for $p$ ranging over a real interval.** ### The maximum norm For $n \\ge 1$ and $x \\in \\mathbb{R}^{n}$ put $$\\lVert x\\rVert_\\infty \\;:=\\; \\max\\{\\, |x_k| \\;:\\; k < n \\,\\},$$ the maximum of a nonempty finite set of reals, which exists and is one of its elements ([[lem-finite-set-has-max]], [[def-max-min]]). **The hypothesis $n \\ge 1$ is required and propagates.** At $n = 0$ the set $\\{|x_k| : k<n\\}$ is empty and has no maximum ([[def-max-min]]). This is the same restriction the published [[lem-metrics-on-rn]] carries, for the same reason, and **every statement on this page that mentions $\\lVert\\cdot\\rVert_\\infty$ inherits it**. The $p$-norms for rational $p \\ge 1$ carry no such restriction: at $n = 0$ each is the empty sum raised to a positive rational power, hence $0$. ### The three cases the rest of the page uses - $\\lVert x\\rVert_1 = \\sum_{k<n}|x_k|$, since $t^{1} = t$ for $t \\ge 0$ ([[lem-rational-power-laws]], and $0^{1} = 0$ by the supplementary clause). - $\\lVert x\\rVert_2 = \\bigl(\\sum_{k<n}|x_k|^{2}\\bigr)^{1/2} = \\sqrt{\\sum_{k<n}x_k^{2}}$, which is exactly the Euclidean norm of [[def-euclidean-inner-product]]: the exponent $2$ agrees with the integer power, so $|x_k|^{2} = x_k^{2}$ ([[lem-of-abs-value]]), and $t^{1/2}$ is the unique nonnegative square root of $t$, which is $\\sqrt{t}$ ([[def-rational-power]], [[thm-of-square-roots]]). **The two notations denote the same function and no second Euclidean norm is introduced.** - $\\lVert x\\rVert_\\infty$ as above, for $n \\ge 1$. That each of these is a norm in the sense of [[def-norm-and-normed-space]], and that the metrics they induce are exactly the published $d_1$, $d_2$ and $d_\\infty$ of [[lem-metrics-on-rn]], is [[lem-p-norms-are-norms-and-induce-the-published-metrics]]; it is proved there and is not assumed here.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.2",
        "3.2",
        "4.1",
        "5.1"
      ]
    },
    {
      "fact": "L6",
      "source": "def-norm-and-normed-space",
      "source_section": "Definition",
      "quote": "Throughout this page $\\mathbb{R}$ is the complete ordered field ([[def-complete-ordered-field]]) constructed in this library, in particular a field, so that \"vector space\" below always means vector space over $\\mathbb{R}$ ([[def-vector-space]]). Let $V$ be a vector space over $\\mathbb{R}$, with zero vector $0_V$. A **norm on $V$** is a function $N : V \\to \\mathbb{R}$ such that for all $u, v \\in V$ and all $\\lambda \\in \\mathbb{R}$: - **(N1) Separation.** $N(v) = 0$ if and only if $v = 0_V$. - **(N2) Absolute homogeneity.** $N(\\lambda v) = |\\lambda|\\,N(v)$, the absolute value being that of [[def-abs-value]]. - **(N3) Triangle inequality.** $N(u + v) \\le N(u) + N(v)$. A **normed space** is a pair $(V, N)$ consisting of a vector space $V$ over $\\mathbb{R}$ and a norm $N$ on it. When only one norm is in play we write $\\lVert v\\rVert$ for $N(v)$; when several are, the norm is always named. **The values of a norm are real numbers.** The codomain is $\\mathbb{R}$, so $N(v)$ is an honest element of the complete ordered field and no infinite value is permitted. This is the same convention [[rem-metric-axiom-conventions]] records for metrics. ### Nonnegativity is a theorem, not an axiom Many texts add a fourth condition $N(v) \\ge 0$. It is redundant. Applying (N2) with $\\lambda = -1$ gives $N(-v) = |-1|\\,N(v) = N(v)$ ([[lem-of-abs-value]], [[lem-vector-space-elementary-consequences]] for $(-1)v = -v$), and then (N3) with $u = v$ and $-v$ gives $$0 \\;=\\; N(0_V) \\;=\\; N\\bigl(v + (-v)\\bigr) \\;\\le\\; N(v) + N(-v) \\;=\\; N(v) + N(v),$$ where $N(0_V) = 0$ is (N1). So $N(v) + N(v) \\ge 0$, and if $N(v) < 0$ then $N(v) + N(v) < 0$ by addition of inequalities, which trichotomy forbids ([[def-complete-ordered-field]]). Hence $N(v) \\ge 0$ for every $v \\in V$. **Consequently the verification of a candidate norm has three things to check and not four**, exactly as the verification of a candidate metric has three and not four ([[def-metric-space]], [[lem-metric-nonnegativity]]). No item in this library assumes nonnegativity of a norm before the argument above. ### The induced metric Let $N$ be a norm on $V$ and define $$d_N(u,v) \\;:=\\; N(u - v) \\qquad (u, v \\in V),$$ where $u - v = u + (-v)$ ([[def-vector-space]]). **Then $d_N$ is a metric on $V$** ([[def-metric-space]]), and the three axioms are the three conditions above, in order: - **(M1)** $d_N(u,v) = 0$ means $N(u-v) = 0$, which by (N1) says $u - v = 0_V$, that is $u = v$; and conversely $d_N(v,v) = N(0_V) = 0$. - **(M2)** $d_N(v,u) = N(v-u) = N\\bigl((-1)(u-v)\\bigr) = |-1|\\,N(u-v) = d_N(u,v)$, by (N2), [[lem-of-abs-value]] and $(-1)w = -w$ ([[lem-vector-space-elementary-consequences]]). - **(M3)** $d_N(u,w) = N\\bigl((u-v) + (v-w)\\bigr) \\le N(u-v) + N(v-w) = d_N(u,v) + d_N(v,w)$, by (N3). A normed space is therefore a metric space, and every notion defined for metric spaces — open set ([[def-metric-topology]]), convergence, Cauchyness, continuity, compactness — is available in it with no further definition. **This library never introduces a second notion of any of them for normed spaces.** ### Two properties an arbitrary metric need not have The metric $d_N$ satisfies, for all $u, v, w \\in V$ and $\\lambda \\in \\mathbb{R}$: - **translation invariance**, $d_N(u + w, v + w) = N\\bigl((u+w)-(v+w)\\bigr) = N(u-v) = d_N(u,v)$; - **absolute homogeneity**, $d_N(\\lambda u, \\lambda v) = N\\bigl(\\lambda(u-v)\\bigr) = |\\lambda|\\,d_N(u,v)$, by (N2). **Not every metric on a vector space arises from a norm**, and homogeneity is what fails. The published bounded remetrisation [[lem-bounded-remetrisation]] replaces a metric $d$ by $d' = \\min\\{d, 1\\}$, a metric with the same topology whose values never exceed $1$; on a vector space $V$ containing a vector $v$ with $d(v, 0_V) > 0$ this $d'$ cannot be $d_M$ for any norm $M$, since absolute homogeneity would force $d'(\\lambda v, 0_V) = |\\lambda|\\,d'(v, 0_V)$, which is unbounded in $\\lambda$, while $d'$ is bounded by $1$. So the passage from norms to metrics is not reversible, and a statement about a metric on a vector space is strictly weaker than the corresponding statement about a norm.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.2",
        "3.2",
        "4.1",
        "5.1"
      ]
    },
    {
      "fact": "L6",
      "source": "def-the-space-of-summing-directions",
      "source_section": "Definition",
      "quote": "Let $n \\in \\mathbb{N}$ with $n \\ge 1$ and let $(x_k)$ be a sequence in $\\mathbb{R}^{n}$ ([[def-series-of-vectors-and-rearrangement]]). Define $$\\Gamma \\;:=\\; \\Bigl\\{\\, a \\in \\mathbb{R}^{n} \\;:\\; \\sum_k \\bigl|\\langle a, x_k\\rangle\\bigr| \\text{ converges} \\,\\Bigr\\}, \\qquad \\Gamma^{\\perp} \\;:=\\; \\bigl\\{\\, y \\in \\mathbb{R}^{n} \\;:\\; \\langle a, y\\rangle = 0 \\text{ for every } a \\in \\Gamma \\,\\bigr\\},$$ the inner product being the Euclidean one ([[def-euclidean-inner-product]]) and the series that of [[def-series]]. Elements of $\\Gamma$ are the **summing directions** of $(x_k)$: those $a$ for which the real series of the projections $\\langle a, x_k\\rangle$ converges absolutely ([[def-absolute-and-conditional-convergence]]). Both sets depend on the sequence $(x_k)$; when several are in play the notation is $\\Gamma(x)$ and $\\Gamma(x)^{\\perp}$. **Phrased with the inner product, deliberately.** The classical statement uses linear functionals and the dual space. This library has no definition of a linear map at this point in the reading order — the page that introduces linear maps, rank-nullity and quotient spaces comes **earlier in the plan order** and is not yet built — so writing $\\Gamma$ with functionals would mint that page's canonical object here. The two descriptions agree on $\\mathbb{R}^{n}$, and nothing on this page depends on their agreement. ### Both are linear subspaces **$\\Gamma$ is a linear subspace of $\\mathbb{R}^{n}$** ([[def-linear-subspace]]). It is nonempty: $\\langle 0, x_k\\rangle = 0$ for every $k$ by bilinearity, and the series with all terms $0$ converges. For $\\lambda \\in \\mathbb{R}$ and $a, b \\in \\Gamma$, bilinearity and the absolute value laws give $$\\bigl|\\langle \\lambda a + b, x_k\\rangle\\bigr| \\;=\\; \\bigl|\\lambda\\langle a,x_k\\rangle + \\langle b,x_k\\rangle\\bigr| \\;\\le\\; |\\lambda|\\,\\bigl|\\langle a,x_k\\rangle\\bigr| + \\bigl|\\langle b,x_k\\rangle\\bigr|$$ ([[lem-of-abs-value]]), and the series of the right-hand side converges by [[lem-series-linearity]] clauses 1 and 2, so the left-hand series converges by the comparison test ([[thm-direct-comparison-test]], the terms being nonnegative). By the one-step subspace test ([[lem-linear-subspace-criterion]]), $\\Gamma$ is a linear subspace. **$\\Gamma^{\\perp}$ is a linear subspace of $\\mathbb{R}^{n}$.** It contains $0$, and for $\\lambda \\in \\mathbb{R}$, $y, z \\in \\Gamma^{\\perp}$ and $a \\in \\Gamma$, bilinearity gives $\\langle a, \\lambda y + z\\rangle = \\lambda\\langle a,y\\rangle + \\langle a,z\\rangle = 0$; again [[lem-linear-subspace-criterion]] applies. Equivalently $\\Gamma^{\\perp}$ is the intersection of the linear subspaces $\\{y : \\langle a,y\\rangle = 0\\}$ over $a \\in \\Gamma$, a nonempty family since $0 \\in \\Gamma$, and [[lem-intersection-of-linear-subspaces]] gives the same conclusion. ### $\\Gamma$ is everything exactly when the series converges absolutely **If $\\sum x_k$ converges absolutely then $\\Gamma = \\mathbb{R}^{n}$.** For any $a$, Cauchy-Schwarz gives $|\\langle a,x_k\\rangle| \\le \\lVert a\\rVert_2\\lVert x_k\\rVert_2$ ([[thm-cauchy-schwarz-and-the-euclidean-norm]]), and $\\sum_k \\lVert a\\rVert_2\\lVert x_k\\rVert_2$ converges by [[lem-series-linearity]] clause 2; the comparison test gives $a \\in \\Gamma$. **Conversely, if $\\Gamma = \\mathbb{R}^{n}$ then $\\sum x_k$ converges absolutely.** Each standard basis vector $e_j$ lies in $\\Gamma$, and $\\langle e_j, x_k\\rangle = (x_k)_j$ ([[lem-standard-basis-of-f-n]], [[def-euclidean-inner-product]]), so each real series $\\sum_k |(x_k)_j|$ converges. A finite sum of convergent series converges, by [[lem-series-linearity]] clause 1 and induction on the number of summands ([[thm-induction-principle]], [[lem-finite-sum-laws]], [[def-finite-sum]]), so $\\sum_k \\sum_{j<n}|(x_k)_j| = \\sum_k \\lVert x_k\\rVert_1$ converges; and $\\lVert x_k\\rVert_2 \\le \\lVert x_k\\rVert_1$ ([[lem-every-norm-on-rn-is-continuous-for-the-euclidean-metric]] clause 3, [[def-p-norms-on-rn]]), so $\\sum_k\\lVert x_k\\rVert_2$ converges by the comparison test. **That equivalence is what makes the containment theorem below contain [[thm-absolute-convergence-in-rn]] as a special case**: absolute convergence gives $\\Gamma = \\mathbb{R}^{n}$, hence $\\Gamma^{\\perp} = \\{0\\}$ (any $y \\in \\Gamma^{\\perp}$ satisfies $\\langle y,y\\rangle = 0$ and so $y = 0$ by positive definiteness), and the affine subspace below collapses to a point. ### Affine subspaces The library has no notion of an affine subspace, so one is fixed here. For a linear subspace $W \\subseteq \\mathbb{R}^{n}$ and $s \\in \\mathbb{R}^{n}$, the **affine subspace through $s$ with direction $W$** is the coset $$s + W \\;:=\\; \\{\\, s + w \\;:\\; w \\in W \\,\\} .$$ **A coset is determined by $W$ together with any one of its points.** If $p \\in s + W$, say $p = s + w_0$ with $w_0 \\in W$, then $p + W = s + W$: every $p + w = s + (w_0 + w)$ lies in $s+W$ because $W$ is closed under addition, and every $s + w = p + (w - w_0)$ lies in $p + W$ because $W$ is closed under addition and under multiplication by $-1$ ([[def-linear-subspace]], [[def-vector-space]]). In particular $s + W = s' + W$ if and only if $s - s' \\in W$.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.2",
        "3.2",
        "4.1",
        "5.1"
      ]
    },
    {
      "fact": "L6",
      "source": "thm-of-square-roots",
      "source_section": "Statement",
      "quote": "Let $F$ be a complete ordered field ([[def-complete-ordered-field]]). Then every $a \\in F$ with $a \\ge 0$ has a **unique** $s \\in F$ with $s \\ge 0$ and $s^2 = a$; we write $s = \\sqrt{a}$. Consequently the positive elements of $F$ are exactly the nonzero squares: $x > 0$ if and only if $x = y^2$ for some $y \\neq 0$.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.2",
        "3.2",
        "4.1",
        "5.1"
      ]
    },
    {
      "fact": "L6",
      "source": "def-integer-power",
      "source_section": "Definition",
      "quote": "Let $a \\in \\mathbb{R}$, where $\\mathbb{R}$ is the ambient ordered field ([[def-ordered-field]], [[def-field]]). **Natural exponents.** By the recursion theorem ([[thm-recursion]]) applied to the set $\\mathbb{R}$, the starting element $1$ and the function $f(x) = x \\cdot a$, there is a unique function $\\mathbb{N} \\to \\mathbb{R}$, written $n \\mapsto a^n$, with $$a^0 = 1, \\qquad a^{n+1} = a^n \\cdot a \\quad (n \\in \\mathbb{N}).$$ Thus $a^1 = a$, $a^2 = a \\cdot a$, and so on. Note that this is defined for **every** $a$, including $a = 0$. **Negative exponents.** If $a \\ne 0$ and $n \\in \\mathbb{N}$ with $n \\ge 1$, set $$a^{-n} := (a^n)^{-1}.$$ **Why that is legitimate.** The right-hand side presupposes that $a^n$ is invertible, that is, that $a^n \\ne 0$. This is a proof obligation and not an observation, and it is discharged by claim 2 of [[lem-power-laws]]: for $a \\ne 0$ in a field, $a^n \\ne 0$ for every $n \\in \\mathbb{N}$, proved there by induction on $n$ from the fact that a field has no zero divisors ([[lem-of-no-zero-divisors]]). That lemma is a statement *about* the operation introduced here, so it depends on this definition and is recorded in this item's `justified_by` rather than in its `deps` (SCHEMA §3). Given $a^n \\ne 0$, the value $(a^n)^{-1}$ is a single well-determined element, because multiplicative inverses in a field are unique ([[lem-of-inverse-unique]]). **Integer exponents.** Every integer $m$ ([[def-integers]]) is either $\\iota(n)$ or $-\\iota(n)$ for a unique natural $n$, where $\\iota$ is the embedding $\\mathbb{N} \\to \\mathbb{Z}$ ([[lem-nat-embeds-int]], [[def-int-operations]]). This too is a citation and not a slogan: the order on $\\mathbb{Z}$ is total ([[thm-int-ordered-ring]]), so $m \\ge 0$ or $m < 0$; the image of $\\iota$ is exactly the set of nonnegative integers, and each of them is $\\iota(n)$ for a unique natural $n$ ([[lem-nat-embeds-int]]); and if $m < 0$ then $-m > 0$, by compatibility of the order with addition ([[thm-int-ordered-ring]]), so $-m = \\iota(n)$ and $m = -\\iota(n)$, with $n$ unique because $\\iota$ is injective. The two clauses above therefore define $a^m$ for every $m \\in \\mathbb{Z}$ whenever $a \\ne 0$, and for every $m \\in \\mathbb{N}$ for arbitrary $a$. The clauses are consistent where they overlap: the only overlap is $m = 0$, where $-\\iota(0) = \\iota(0)$ and $(a^0)^{-1} = 1^{-1} = 1 = a^0$.",
      "quote_selection": "full-source-section",
      "uses": [
        "2.2",
        "3.2",
        "4.1",
        "5.1"
      ]
    },
    {
      "fact": "L7",
      "source": "lem-series-linearity",
      "source_section": "Statement",
      "quote": "Let $(a_k)$ and $(b_k)$ be sequences of reals whose series converge ([[def-series]]), and let $c \\in \\mathbb{R}$. Then: 1. $\\sum (a_k + b_k)$ converges, with $\\displaystyle\\sum_{k=0}^{\\infty}(a_k + b_k) = \\sum_{k=0}^{\\infty} a_k + \\sum_{k=0}^{\\infty} b_k$; 2. $\\sum c\\,a_k$ converges, with $\\displaystyle\\sum_{k=0}^{\\infty} c\\,a_k = c \\sum_{k=0}^{\\infty} a_k$. Moreover, for $c \\ne 0$ and an arbitrary sequence $(a_k)$, whose series is not assumed to converge: 3. $\\sum c\\,a_k$ converges **if and only if** $\\sum a_k$ converges. Equivalently, $\\sum a_k$ diverges if and only if $\\sum c\\,a_k$ diverges. Claim 3 is the form used whenever a comparison is made against a constant multiple of a known series.",
      "quote_selection": "full-source-section",
      "uses": [
        "3.2"
      ]
    },
    {
      "fact": "L8",
      "source": "thm-rearrangement-sums-lie-in-an-affine-subspace",
      "source_section": "Statement",
      "quote": "Let $n \\in \\mathbb{N}$ with $n \\ge 1$, let $(x_k)$ be a sequence in $\\mathbb{R}^{n}$ whose series converges ([[def-series-of-vectors-and-rearrangement]]) and write $s := \\sum_{k=0}^{\\infty}x_k$. Let $\\Gamma$ and $\\Gamma^{\\perp}$ be as in [[def-the-space-of-summing-directions]]. Then: 1. **Nonemptiness.** $s \\in \\mathcal{S}(x)$, so $\\mathcal{S}(x) \\ne \\varnothing$. 2. **Containment.** $$\\mathcal{S}(x) \\;\\subseteq\\; s + \\Gamma^{\\perp},$$ the affine subspace through $s$ with direction $\\Gamma^{\\perp}$ ([[def-the-space-of-summing-directions]]). Equivalently, $t - s \\in \\Gamma^{\\perp}$ for every rearrangement sum $t$. 3. **The absolutely convergent case.** If $\\sum x_k$ converges absolutely then $\\Gamma = \\mathbb{R}^{n}$, $\\Gamma^{\\perp} = \\{0\\}$, the affine subspace is the single point $\\{s\\}$, and $\\mathcal{S}(x) = \\{s\\}$. 4. **The one-dimensional conditionally convergent case.** Let $n = 1$ and identify $\\mathbb{R}^{1}$ with $\\mathbb{R}$ as in [[def-series-of-vectors-and-rearrangement]]. If $\\sum x_k$ converges conditionally ([[def-absolute-and-conditional-convergence]]) then $\\Gamma = \\{0\\}$, $\\Gamma^{\\perp} = \\mathbb{R}^{1}$, and the containment of clause 2 is an **equality**, $\\mathcal{S}(x) = s + \\Gamma^{\\perp} = \\mathbb{R}^{1}$, by the published [[thm-riemann-series-theorem]]. **What this theorem does not say, stated here and repeated in the Remarks.** It proves a **containment** and nothing more. Whether $\\mathcal{S}(x)$ is all of $s + \\Gamma^{\\perp}$ when $n \\ge 2$ is **not settled anywhere on this page**, and no item on this page asserts anything about it in either direction. Clause 4 is the case $n = 1$, where the answer is supplied by a published theorem about the real line; it is not evidence for any statement in higher dimensions.",
      "quote_selection": "full-source-section",
      "uses": [
        "3.3",
        "6.1"
      ]
    },
    {
      "fact": "L8",
      "source": "thm-riemann-series-theorem",
      "source_section": "Statement",
      "quote": "Let $(a_k)$ be a sequence of reals whose series converges conditionally ([[def-absolute-and-conditional-convergence]]). Let $\\alpha, \\beta \\in \\overline{\\mathbb{R}}$ ([[def-extended-reals]]) with $\\alpha \\le \\beta$. Then there is a bijection $\\sigma : \\mathbb{N} \\to \\mathbb{N}$ ([[def-injection-surjection-bijection]]) such that the partial sums $T_n = \\sum_{k<n} a_{\\sigma(k)}$ of the rearranged series ([[def-rearrangement-and-unconditional-convergence]]) satisfy $$\\liminf_{n} T_n = \\alpha, \\qquad \\limsup_{n} T_n = \\beta$$ ([[def-limsup-liminf]]). In particular: 1. for every $c \\in \\mathbb{R}$, taking $\\alpha = \\beta = c$, there is a rearrangement of $\\sum a_k$ that converges with sum $c$; 2. taking $\\alpha = \\beta = +\\infty$, there is a rearrangement whose partial sums diverge to $+\\infty$ ([[def-divergence-to-infinity]]), and taking $\\alpha = \\beta = -\\infty$, one whose partial sums diverge to $-\\infty$; 3. taking $\\alpha < \\beta$, there is a rearrangement whose partial sums oscillate, with limit inferior exactly $\\alpha$ and limit superior exactly $\\beta$. So the sum of a conditionally convergent series is an artefact of the order in which its terms are written, and every prescribed asymptotic behaviour is attainable. Contrast [[thm-dirichlet-rearrangement]], where absolute convergence makes the sum independent of the order. **The construction.** Write $P := \\{k : a_k \\ge 0\\}$ and $N := \\{k : a_k < 0\\}$, which partition $\\mathbb{N}$, and enumerate each increasingly as $(p_i)$ and $(q_l)$. Fix real sequences $(u_j)$ and $(v_j)$ with $u_j \\le v_j$ and $u_j \\le v_{j+1}$ for every $j$; these are the *targets*. The rearrangement is produced one index at a time by a greedy rule: **while the running sum is at most the current upper target, take the next unused nonnegative term; once it exceeds that target, take negative terms until the running sum falls below the current lower target; then move to the next pair of targets and repeat.** Both supplies are inexhaustible, because for a conditionally convergent series both $\\sum a_k^{+}$ and $\\sum a_k^{-}$ diverge to $+\\infty$ ([[lem-positive-and-negative-parts]]); and the overshoot at each turning point is at most the term just used, which tends to $0$ because $a_k \\to 0$ ([[lem-nth-term-test]]). Those two facts are the whole theorem.",
      "quote_selection": "full-source-section",
      "uses": [
        "3.3",
        "6.1"
      ]
    },
    {
      "fact": "L8",
      "source": "def-absolute-and-conditional-convergence",
      "source_section": "Definition",
      "quote": "Let $(a_k)$ be a sequence of reals, with series $\\sum a_k$ and partial sums $s_n = \\sum_{k<n} a_k$ as in [[def-series]], and let $|x|$ be the absolute value ([[def-abs-value]]). **Absolute convergence.** The series $\\sum a_k$ **converges absolutely** when the series $\\sum |a_k|$ converges ([[def-series]]). Since $|a_k| \\ge 0$ for every $k$ ([[lem-of-abs-value]]), this is a statement about a series of nonnegative terms. **Conditional convergence.** The series $\\sum a_k$ **converges conditionally** when it converges ([[def-series]], [[def-real-limit]]) and does *not* converge absolutely. So a convergent series is exactly one of the two: absolutely convergent or conditionally convergent, according as $\\sum |a_k|$ converges or not. **One implication is already proved, and is not reproved anywhere on this page.** [[lem-absolute-convergence-implies-convergence]] states that if $\\sum |a_k|$ converges then $\\sum a_k$ converges. That lemma was coined and proved on the previous page of this track, where the root and ratio tests need it; this page names it and builds on it. In particular an absolutely convergent series is a convergent series, so the two words above really do partition the convergent series, and \"conditionally convergent\" is not vacuous by accident: the alternating harmonic series is a witness, and the witness is exhibited in [[fs-convergent-implies-absolutely-convergent]]. **General starting index.** Let $m \\in \\mathbb{N}$ and let $(a_k)_{k \\ge m}$ be a family from $m$ ([[def-series]]). The series $\\sum_{k \\ge m} a_k$ **converges absolutely** when $\\sum_{k \\ge m} |a_k|$ converges, and **converges conditionally** when it converges and does not converge absolutely. By [[def-series]] both statements are the corresponding statements for the shifted sequence $j \\mapsto a_{j+m}$, so nothing new is being defined and every result below transfers to a general starting index in the same way, exactly as [[lem-absolute-convergence-implies-convergence]] already records for the one implication it proves.",
      "quote_selection": "full-source-section",
      "uses": [
        "3.3",
        "6.1"
      ]
    },
    {
      "fact": "L8",
      "source": "def-injection-surjection-bijection",
      "source_section": "Definition",
      "quote": "Let $A$ and $B$ be sets and let $f : A \\to B$ be a function ([[def-function]]). - $f$ is **injective** (one-to-one) if $f(x) = f(y)$ implies $x = y$, for all $x, y \\in A$. - $f$ is **surjective** (onto) if for every $b \\in B$ there is some $x \\in A$ with $f(x) = b$; equivalently, the image $f[A] := \\{ f(x) : x \\in A \\}$ equals $B$. - $f$ is **bijective** if it is both injective and surjective. For $S \\subseteq A$ we write $f[S] = \\{ f(x) : x \\in S \\}$ for the image of $S$, and for $T \\subseteq B$ we write $f^{-1}[T] = \\{ x \\in A : f(x) \\in T \\}$ for the preimage of $T$; these are the image and preimage of a set under $f$ read as a relation ([[def-image-and-preimage-under-a-relation]]).",
      "quote_selection": "full-source-section",
      "uses": [
        "3.3",
        "6.1"
      ]
    }
  ],
  "derivations": [
    {
      "id": "step-1.1",
      "claim": "$(b_k)$ is positive, nonincreasing and converges to $0$: positivity and monotonicity from $0 < \\iota(k+1) < \\iota(k+2)$, and convergence because for a rational $\\varepsilon>0$ an index $K$ with $1/\\iota(K+1)<\\varepsilon$ gives $b_k \\le b_K < \\varepsilon$ for $k \\ge K$.",
      "step": "1.1",
      "inputs": [
        "L2"
      ]
    },
    {
      "id": "step-1.2",
      "claim": "The second coordinate sequence is constantly $0$, so its series converges with sum $0$.",
      "step": "1.2",
      "inputs": [
        "L5"
      ]
    },
    {
      "id": "step-2.1",
      "claim": "By the alternating series test $\\sum_k c_k = \\sum_k \\varepsilon_k b_k$ converges; write $S$ for its sum.",
      "step": "2.1",
      "inputs": [
        "step 1.1",
        "L3"
      ]
    },
    {
      "id": "step-2.2",
      "claim": "$\\lVert x_k\\rVert_2 = \\sqrt{c_k^{2}+0} = |c_k| = |\\varepsilon_k| b_k = b_k$, and $\\sum_k b_k$ is the harmonic series, which diverges; so $\\sum x_k$ does not converge absolutely, which is clause 2.",
      "step": "2.2",
      "inputs": [
        "step 1.1",
        "L1",
        "L4",
        "L6"
      ]
    },
    {
      "id": "step-3.1",
      "claim": "By componentwise convergence, $\\sum x_k$ converges with sum $s = (S,0)$, which is clause 1.",
      "step": "3.1",
      "inputs": [
        "step 2.1",
        "step 1.2",
        "L5"
      ]
    },
    {
      "id": "step-3.2",
      "claim": "For $a = (a_0,a_1) \\in \\mathbb{R}^{2}$: $\\langle a, x_k\\rangle = a_0 c_k$, so $|\\langle a,x_k\\rangle| = |a_0|\\,b_k$. If $a_0 = 0$ every term is $0$ and the series converges; if $a_0 \\ne 0$ then $|a_0| > 0$ and convergence of $\\sum_k |a_0| b_k$ would give convergence of $\\sum_k b_k$, which is false.",
      "step": "3.2",
      "inputs": [
        "step 2.2",
        "L1",
        "L6",
        "L7"
      ]
    },
    {
      "id": "step-3.3",
      "claim": "Conversely let $t \\in \\mathbb{R}$. The real series $\\sum_k c_k$ converges by step 2.1 and does not converge absolutely by step 2.2, so it converges conditionally, and the Riemann series theorem supplies a bijection $\\sigma$ of $\\mathbb{N}$ with $\\sum_k c_{\\sigma(k)} = t$. The rearranged vector series $\\sum_k x_{\\sigma(k)}$ has first coordinate series $\\sum_k c_{\\sigma(k)}$ and second coordinate series constantly $0$, so by componentwise convergence it converges to $(t,0)$; hence $(t,0) \\in \\mathcal{S}(x)$.",
      "step": "3.3",
      "inputs": [
        "step 2.1",
        "step 2.2",
        "L5",
        "L8"
      ]
    },
    {
      "id": "step-4.1",
      "claim": "Hence $\\Gamma = \\{a : a_0 = 0\\} = \\{(0,t) : t \\in \\mathbb{R}\\}$, the set of scalar multiples of $e_1$.",
      "step": "4.1",
      "inputs": [
        "step 3.2",
        "L6"
      ]
    },
    {
      "id": "step-5.1",
      "claim": "For $y = (y_0,y_1)$: $y \\in \\Gamma^{\\perp}$ means $\\langle (0,t), y\\rangle = t\\,y_1 = 0$ for every real $t$, which at $t = 1$ forces $y_1 = 0$, and conversely $y_1 = 0$ makes every such product $0$. So $\\Gamma^{\\perp} = \\{(t,0) : t \\in \\mathbb{R}\\}$, the set of scalar multiples of $e_0$, and clause 3 is proved.",
      "step": "5.1",
      "inputs": [
        "step 4.1",
        "L6"
      ]
    },
    {
      "id": "step-6.1",
      "claim": "By the containment theorem, $\\mathcal{S}(x) \\subseteq s + \\Gamma^{\\perp} = \\{\\,(S+t,\\ 0) : t \\in \\mathbb{R}\\,\\} = \\{\\,(w,0) : w\\in\\mathbb{R}\\,\\}$.",
      "step": "6.1",
      "inputs": [
        "step 3.1",
        "step 5.1",
        "L8"
      ]
    },
    {
      "id": "step-7.1",
      "claim": "Steps 6.1 and 3.3 give $\\mathcal{S}(x) = s + \\Gamma^{\\perp}$, which is clause 4.",
      "step": "7.1",
      "inputs": [
        "step 6.1",
        "step 3.3"
      ]
    }
  ],
  "routine_steps": [],
  "boundaries": [
    {
      "case": "empty",
      "status": "not_applicable",
      "reason": "ex-gamma-and-its-complement-computed-for-a-plane-series: the Statement introduces no possibly empty family requiring a witness; its sequence domains are N or its displayed witness has a fixed nonempty domain."
    },
    {
      "case": "zero",
      "status": "checked",
      "evidence": "step 3.1: By componentwise convergence, $\\sum x_k$ converges with sum $s = (S,0)$, which is clause 1."
    },
    {
      "case": "one",
      "status": "not_applicable",
      "reason": "ex-gamma-and-its-complement-computed-for-a-plane-series: there is no cardinal, dimension, or exponent parameter with a separate value-one branch in this claim."
    },
    {
      "case": "degenerate",
      "status": "not_applicable",
      "reason": "ex-gamma-and-its-complement-computed-for-a-plane-series: the Statement has no collapse, coincidence, constant-family, or equality-case branch beyond cases already included by its universal estimates."
    },
    {
      "case": "endpoints",
      "status": "not_applicable",
      "reason": "ex-gamma-and-its-complement-computed-for-a-plane-series: no closed-interval endpoint, exponent endpoint, or finite-index endpoint affects the assertion."
    },
    {
      "case": "nonempty-choice",
      "status": "not_applicable",
      "reason": "ex-gamma-and-its-complement-computed-for-a-plane-series: the proof makes no choice from a family whose nonemptiness is not already supplied; any witness used is explicit or uniquely determined."
    },
    {
      "case": "iff-forward",
      "status": "not_applicable",
      "reason": "ex-gamma-and-its-complement-computed-for-a-plane-series: the asserted result has no biconditional requiring a forward implication; any “if and only if” appearing inside a cited definition is not a new proof obligation here."
    },
    {
      "case": "iff-reverse",
      "status": "not_applicable",
      "reason": "ex-gamma-and-its-complement-computed-for-a-plane-series: the asserted result has no biconditional requiring a reverse implication; any equivalence used as a dependency is consumed only in the direction named by the numbered proof."
    }
  ],
  "finite_smoke": [],
  "risk_review": {
    "status": "pending",
    "reviewer": "Alpha",
    "notes": "Audit-Beta captured the A2 contract. Alpha assigns the independent proof-refuter route at A5/A6."
  }
}
```

## Generated audit-manifest relationships

```json
[
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-the-space-of-summing-directions",
    "declared_target": "def-the-space-of-summing-directions",
    "target_statement_provenance": "ai-altered",
    "targetPage": "rn-as-a-normed-space",
    "targetBatch": "wave12-real-analysis",
    "edge_type": "dependency",
    "kind": "same-batch",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-series-of-vectors-and-rearrangement",
    "declared_target": "def-series-of-vectors-and-rearrangement",
    "target_statement_provenance": "ai-altered",
    "targetPage": "rn-as-a-normed-space",
    "targetBatch": "wave12-real-analysis",
    "edge_type": "dependency",
    "kind": "same-batch",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "thm-rearrangement-sums-lie-in-an-affine-subspace",
    "declared_target": "thm-rearrangement-sums-lie-in-an-affine-subspace",
    "target_statement_provenance": "ai-altered",
    "targetPage": "rn-as-a-normed-space",
    "targetBatch": "wave12-real-analysis",
    "edge_type": "dependency",
    "kind": "same-batch",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "thm-componentwise-convergence-and-completeness",
    "declared_target": "thm-componentwise-convergence-and-completeness",
    "target_statement_provenance": "ai-altered",
    "targetPage": "rn-as-a-normed-space",
    "targetBatch": "wave12-real-analysis",
    "edge_type": "dependency",
    "kind": "same-batch",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "thm-alternating-series-test",
    "declared_target": "thm-alternating-series-test",
    "target_statement_provenance": "literature-derived",
    "targetPage": "absolute-convergence-and-rearrangement",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "thm-p-series-rational",
    "declared_target": "thm-p-series-rational",
    "target_statement_provenance": "ai-altered",
    "targetPage": "series-and-nonnegative-tests",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "thm-riemann-series-theorem",
    "declared_target": "thm-riemann-series-theorem",
    "target_statement_provenance": "ai-altered",
    "targetPage": "absolute-convergence-and-rearrangement",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "lem-series-linearity",
    "declared_target": "lem-series-linearity",
    "target_statement_provenance": "ai-altered",
    "targetPage": "series-and-nonnegative-tests",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "lem-alternating-sequence",
    "declared_target": "lem-alternating-sequence",
    "target_statement_provenance": "ai-altered",
    "targetPage": "monotone-sequences-and-cauchy-completeness",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-monotone-sequence",
    "declared_target": "def-monotone-sequence",
    "target_statement_provenance": "ai-altered",
    "targetPage": "monotone-sequences-and-cauchy-completeness",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-euclidean-inner-product",
    "declared_target": "def-euclidean-inner-product",
    "target_statement_provenance": "ai-altered",
    "targetPage": "rn-as-a-normed-space",
    "targetBatch": "wave12-real-analysis",
    "edge_type": "dependency",
    "kind": "same-batch",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-p-norms-on-rn",
    "declared_target": "def-p-norms-on-rn",
    "target_statement_provenance": "ai-altered",
    "targetPage": "rn-as-a-normed-space",
    "targetBatch": "wave12-real-analysis",
    "edge_type": "dependency",
    "kind": "same-batch",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-norm-and-normed-space",
    "declared_target": "def-norm-and-normed-space",
    "target_statement_provenance": "ai-altered",
    "targetPage": "rn-as-a-normed-space",
    "targetBatch": "wave12-real-analysis",
    "edge_type": "dependency",
    "kind": "same-batch",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-series",
    "declared_target": "def-series",
    "target_statement_provenance": "ai-altered",
    "targetPage": "series-and-nonnegative-tests",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-absolute-and-conditional-convergence",
    "declared_target": "def-absolute-and-conditional-convergence",
    "target_statement_provenance": "ai-altered",
    "targetPage": "absolute-convergence-and-rearrangement",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-linear-subspace",
    "declared_target": "def-linear-subspace",
    "target_statement_provenance": "literature-derived",
    "targetPage": "vector-spaces-and-subspaces",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-canonical-natural",
    "declared_target": "def-canonical-natural",
    "target_statement_provenance": "ai-altered",
    "targetPage": "foundations-of-the-real-numbers",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "lem-of-naturals-positive",
    "declared_target": "lem-of-naturals-positive",
    "target_statement_provenance": "ai-altered",
    "targetPage": "foundations-of-the-real-numbers",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "lem-of-inverse-positive",
    "declared_target": "lem-of-inverse-positive",
    "target_statement_provenance": "ai-altered",
    "targetPage": "foundations-of-the-real-numbers",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "cor-archimedean-reciprocal",
    "declared_target": "cor-archimedean-reciprocal",
    "target_statement_provenance": "ai-altered",
    "targetPage": "foundations-of-the-real-numbers",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-integer-power",
    "declared_target": "def-integer-power",
    "target_statement_provenance": "ai-altered",
    "targetPage": "roots-and-rational-powers",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-real-limit",
    "declared_target": "def-real-limit",
    "target_statement_provenance": "ai-altered",
    "targetPage": "construction-of-r-via-cauchy-sequences",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "lem-of-abs-value",
    "declared_target": "lem-of-abs-value",
    "target_statement_provenance": "ai-altered",
    "targetPage": "foundations-of-the-real-numbers",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "lem-standard-basis-of-f-n",
    "declared_target": "lem-standard-basis-of-f-n",
    "target_statement_provenance": "ai-altered",
    "targetPage": "linear-independence-bases-and-dimension",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-injection-surjection-bijection",
    "declared_target": "def-injection-surjection-bijection",
    "target_statement_provenance": "ai-altered",
    "targetPage": "relations-functions-and-quotients",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "thm-of-square-roots",
    "declared_target": "thm-of-square-roots",
    "target_statement_provenance": "ai-altered",
    "targetPage": "foundations-of-the-real-numbers",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  },
  {
    "source": "ex-gamma-and-its-complement-computed-for-a-plane-series",
    "sourcePage": "rn-as-a-normed-space-examples",
    "batch": "wave12-real-analysis",
    "target": "def-rational-power",
    "declared_target": "def-rational-power",
    "target_statement_provenance": "ai-altered",
    "targetPage": "roots-and-rational-powers",
    "targetBatch": null,
    "edge_type": "dependency",
    "kind": "published-backward",
    "requires_semantic_audit": true
  }
]
```

## Relevant current generated-risk rows

```json
[
  {
    "id": "rem-rn-conventions-and-scope",
    "file": "items/rem-rn-conventions-and-scope.md",
    "source": "provenance",
    "cone_size": 7,
    "logical_consumers": [
      "rem-total-derivative-conventions-and-linear-map-seam"
    ],
    "direct_citation_consumers": [
      {
        "id": "cex-the-one-norm-comes-from-no-inner-product",
        "via": [
          "wikilink"
        ]
      },
      {
        "id": "def-euclidean-inner-product",
        "via": [
          "wikilink"
        ]
      },
      {
        "id": "def-norm-and-normed-space",
        "via": [
          "wikilink"
        ]
      },
      {
        "id": "ex-gamma-and-its-complement-computed-for-a-plane-series",
        "via": [
          "wikilink"
        ]
      },
      {
        "id": "rem-total-derivative-conventions-and-linear-map-seam",
        "via": [
          "deps",
          "wikilink"
        ]
      },
      {
        "id": "thm-absolute-convergence-in-rn",
        "via": [
          "wikilink"
        ]
      },
      {
        "id": "thm-rearrangement-sums-lie-in-an-affine-subspace",
        "via": [
          "wikilink"
        ]
      }
    ],
    "disposition": {
      "status": "pending",
      "by": "",
      "notes": ""
    }
  }
]
```

## Full exact-current text of every cited or declared item (28)

### `cor-archimedean-reciprocal`

````markdown
---
id: cor-archimedean-reciprocal
kind: corollary
title: "For every $\\varepsilon > 0$ in a complete ordered field there is a natural $n \\ge 1$ with $1/n < \\varepsilon$"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-altered
deps: [thm-of-archimedean, lem-of-inverse-positive, def-complete-ordered-field, def-ordered-field, def-field]
justified_by: []
aliases: []
landmark: false
proof_strategy: direct
verification:
  precheck: pass
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-26
  audited: 2026-07-26
sources:
  scraped: []
  references:
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 1 (Thm 1.20(a) and its corollaries)"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "T. Tao, Analysis I, 3rd ed., §5.4 (Prop. 5.4.12, the Archimedean property)"
      url: "https://terrytao.wordpress.com/books/analysis-i/"
    - title: "Archimedean property (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Archimedean_property"
    - title: "UTSA Mathematics: The Archimedean property"
      url: "https://mathresearch.utsa.edu/wiki/index.php?title=Real_Numbers%3AArchimedean_Property"
---

## Statement

Let $F$ be a complete ordered field ([[def-complete-ordered-field]]) and let
$\varepsilon \in F$ with $\varepsilon > 0$. Then there is a natural number
$n \ge 1$ such that

$$\frac{1}{n \cdot 1_F} < \varepsilon ,$$

where $n \cdot 1_F$ is the canonical natural of $F$ ([[thm-of-archimedean]]) and
$1/(n \cdot 1_F)$ is its multiplicative inverse ([[def-field]]). As is standard
we abbreviate $n \cdot 1_F$ to $n$ and write the conclusion $1/n < \varepsilon$.

This is the **reciprocal form** of the Archimedean property.
[[thm-of-archimedean]] on its own delivers only the assertion that the canonical
naturals are cofinal, $x < n \cdot 1_F$; the form actually used in analysis, that
the reciprocals of the naturals get below every positive bound, is the statement
above, and it is recorded separately so that no proof has to reconstruct the
inversion step in passing.

## Facts & Assumptions

**Given:** A complete ordered field $F$ and an element $\varepsilon \in F$ with $\varepsilon > 0$.

[L1] Archimedean property: for every $x \in F$ there is a natural number $n \ge 1$ with $x < n \cdot 1_F$ ([[thm-of-archimedean]], [[def-complete-ordered-field]]).

[L2] Inverses and order: if $a > 0$ then $a^{-1} > 0$, and if $0 < a < b$ then $0 < b^{-1} < a^{-1}$ ([[lem-of-inverse-positive]], [[def-ordered-field]]).

[L3] Field arithmetic: an element $a$ with $a > 0$ is nonzero by trichotomy, hence has a multiplicative inverse $a^{-1}$, and $(a^{-1})^{-1} = a$ ([[def-field]], [[def-ordered-field]]).

## Proof

**Proof technique:** direct.

1.1 Since $\varepsilon > 0$, trichotomy gives $\varepsilon \ne 0$, so $\varepsilon^{-1}$ exists, and $\varepsilon^{-1} > 0$. [given, L2, L3]

2.1 Apply [L1] to $x = \varepsilon^{-1}$: fix a natural number $n \ge 1$ with $\varepsilon^{-1} < n \cdot 1_F$. [step 1.1, L1, choose]

3.1 Chaining the two displayed inequalities gives $0 < \varepsilon^{-1} < n \cdot 1_F$; in particular $n \cdot 1_F > 0$, so $n \cdot 1_F \ne 0$ and $1/(n \cdot 1_F)$ is defined. [step 1.1, step 2.1, L3]

4.1 Apply the second claim of [L2] with $a = \varepsilon^{-1}$ and $b = n \cdot 1_F$: $0 < (n \cdot 1_F)^{-1} < (\varepsilon^{-1})^{-1}$. [step 3.1, L2]

5.1 By [L3], $(\varepsilon^{-1})^{-1} = \varepsilon$, so the natural number $n \ge 1$ fixed in step 2.1 satisfies $1/(n \cdot 1_F) < \varepsilon$, which is the assertion. [step 4.1, L3] ∎

## Remarks

- **Monotonicity gives the eventual form for free.** If $m \ge n \ge 1$ then
  $m \cdot 1_F \ge n \cdot 1_F > 0$, because $k \mapsto k \cdot 1_F$ is strictly
  increasing on the naturals $\ge 1$ ([[lem-of-naturals-positive]]), and so
  $1/(m \cdot 1_F) \le 1/(n \cdot 1_F) < \varepsilon$ by [[lem-of-inverse-positive]]
  again. So the corollary yields not merely one index but a threshold: every
  $m \ge n$ satisfies $1/m < \varepsilon$. That one extra line is what a
  convergence proof needs, and it is left to the caller rather than folded into
  the statement, because the caller usually has a threshold of its own to combine
  it with.

- **Completeness is used only through [[thm-of-archimedean]].** Nothing here
  needs the least-upper-bound property directly. The corollary therefore holds
  verbatim in any Archimedean ordered field, in particular in $\mathbb{Q}$, and
  it fails in a non-Archimedean ordered field, where an infinitesimal
  $\varepsilon > 0$ is below every $1/n$ by construction.

- The equivalence is exact: the reciprocal form implies the cofinal form back
  again, since given $x > 0$ one applies it to $\varepsilon = 1/x$. The two are
  the same property written on the two sides of the inversion, and only the
  direction proved above is used in this library.
````

### `def-absolute-and-conditional-convergence`

````markdown
---
id: def-absolute-and-conditional-convergence
kind: definition
title: "Absolutely convergent and conditionally convergent series, and the general starting index"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [def-series, lem-absolute-convergence-implies-convergence, def-abs-value, lem-of-abs-value, def-real-limit]
justified_by: []
aliases: []
landmark: true
verification:
  precheck: n/a
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-27
  audited: 2026-07-27
sources:
  scraped: []
  references:
    - title: "Absolute convergence (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Absolute_convergence"
    - title: "Conditional convergence (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Conditional_convergence"
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 3"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "John K. Hunter, An Introduction to Real Analysis"
      url: "https://www.math.ucdavis.edu/~hunter/intro_analysis_pdf/intro_analysis.pdf"
    - title: "N. Donaldson, Math 140A: Series"
      url: "https://www.math.uci.edu/~ndonalds/math140a/3series.html"
pipeline_run: null
---

## Definition

Let $(a_k)$ be a sequence of reals, with series $\sum a_k$ and partial sums
$s_n = \sum_{k<n} a_k$ as in [[def-series]], and let $|x|$ be the absolute value
([[def-abs-value]]).

**Absolute convergence.** The series $\sum a_k$ **converges absolutely** when the
series $\sum |a_k|$ converges ([[def-series]]). Since $|a_k| \ge 0$ for every $k$
([[lem-of-abs-value]]), this is a statement about a series of nonnegative terms.

**Conditional convergence.** The series $\sum a_k$ **converges conditionally**
when it converges ([[def-series]], [[def-real-limit]]) and does *not* converge
absolutely.

So a convergent series is exactly one of the two: absolutely convergent or
conditionally convergent, according as $\sum |a_k|$ converges or not.

**One implication is already proved, and is not reproved anywhere on this page.**
[[lem-absolute-convergence-implies-convergence]] states that if $\sum |a_k|$
converges then $\sum a_k$ converges. That lemma was coined and proved on the
previous page of this track, where the root and ratio tests need it; this page
names it and builds on it. In particular an absolutely convergent series is a
convergent series, so the two words above really do partition the convergent
series, and "conditionally convergent" is not vacuous by accident: the alternating
harmonic series is a witness, and the witness is exhibited in
[[fs-convergent-implies-absolutely-convergent]].

**General starting index.** Let $m \in \mathbb{N}$ and let $(a_k)_{k \ge m}$ be a
family from $m$ ([[def-series]]). The series $\sum_{k \ge m} a_k$ **converges
absolutely** when $\sum_{k \ge m} |a_k|$ converges, and **converges
conditionally** when it converges and does not converge absolutely. By
[[def-series]] both statements are the corresponding statements for the shifted
sequence $j \mapsto a_{j+m}$, so nothing new is being defined and every result
below transfers to a general starting index in the same way, exactly as
[[lem-absolute-convergence-implies-convergence]] already records for the one
implication it proves.

## Remarks

- **Absolute convergence is a condition on the terms, not on the sum.** It says
  the series of absolute values converges, and it says nothing about the value of
  $\sum_{k=0}^{\infty} a_k$. The two sums are in general different, and no
  statement here identifies them.

- **Why the distinction earns a page.** Every result on this page separates the
  two classes. An absolutely convergent series may be reordered at will
  ([[thm-dirichlet-rearrangement]]) and multiplied by another
  ([[thm-mertens]]); a conditionally convergent one may be reordered to any sum
  whatever ([[thm-riemann-series-theorem]]). The difference is not one of degree.

- **A series of nonnegative terms converges absolutely if it converges at all**,
  since then $|a_k| = a_k$. So the distinction is invisible for the comparison,
  condensation, Raabe, Gauss and Kummer tests of the previous page, all of which
  assume terms of one sign. It is not invisible on that page as a whole: the root
  and ratio tests are stated for terms of arbitrary sign and reach convergence of
  $\sum a_k$ precisely through
  [[lem-absolute-convergence-implies-convergence]], which is where the word
  *absolutely convergent* is first used. What that page does not develop, and this
  one does, is everything that separates the two classes rather than the one
  implication those two tests need.
````

### `def-canonical-natural`

````markdown
---
id: def-canonical-natural
kind: definition
title: "The canonical natural $\\iota(n) = n \\cdot 1_F$ of a field"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [def-field, def-natural-numbers, thm-recursion]
justified_by: []
forward_refs: [def-metric-completion]
aliases: []
landmark: false
short: "$\\iota(n) = n \\cdot 1_F$"
verification:
  precheck: n/a
  audited: 2026-07-27
sources:
  scraped: []
  references:
    - title: "Characteristic (algebra) (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Characteristic_(algebra)"
    - title: "T. Tao, Analysis I, 3rd ed."
      url: "https://terrytao.wordpress.com/books/analysis-i/"
    - title: "Elias Zakon, Mathematical Analysis: Natural Numbers and Induction"
      url: "https://math.libretexts.org/Bookshelves/Analysis/Mathematical_Analysis_%28Zakon%29/02%3A_Real_Numbers_and_Fields/2.02%3A_Natural_Numbers._Induction"
pipeline_run: null
---

## Definition

Let $F$ be a field ([[def-field]]) with additive identity $0_F$ and
multiplicative identity $1_F$. Define
$\iota : \mathbb{N} \to F$ by recursion on $\mathbb{N}$
([[def-natural-numbers]], [[thm-recursion]]):

$$\iota(0) \;:=\; 0_F, \qquad \iota(n+1) \;:=\; \iota(n) + 1_F .$$

$\iota(n)$ is the **canonical natural** of $n$ in $F$. It is also written
$n \cdot 1_F$, and for $n \ge 1$ it is $1_F$ added to itself $n$ times.

**Why the notation is needed at all.** A natural number in this library is a von
Neumann natural, that is a set ([[def-natural-numbers]]), and a set is not an
element of $F$. So $1/n$, $n^{\alpha}$ and $x/n$ are not expressions of $F$ when
$n$ is a natural: what they mean is $1/\iota(n)$, $\iota(n)^{\alpha}$ and
$x/\iota(n)$. The map $\iota$ is what carries a counting number into the field,
and writing it is the whole reason a reader meets $1/\iota(k+1)$ where an
informal text would write $1/(k+1)$.

## Remarks

- **Where the index shift comes from.** $\mathbb{N}$ contains $0$
  ([[def-natural-numbers]]) and $\iota(0) = 0_F$, so $1/\iota(k)$ is undefined at
  $k = 0$. A family of reciprocals indexed by $\mathbb{N}$ is therefore written
  over $\iota(k+1)$, which is why the harmonic and telescoping families of this
  library run over $k+1$ rather than over $k$. This is bookkeeping, not a
  restriction: the values are the usual ones.

- **This definition records notation; the arithmetic is proved elsewhere.** That
  $\iota$ is strictly increasing and positive on $n \ge 1$, and that it carries
  sums to sums and products to products, is [[lem-of-naturals-positive]], stated
  for an ordered field. That lemma introduces the same element by the equivalent
  recursion $1 \cdot 1_F = 1_F$, $(n+1) \cdot 1_F = n \cdot 1_F + 1_F$, which
  agrees with the definition above because $\iota(1) = \iota(0) + 1_F = 1_F$.
  Nothing here is new mathematics; the definition exists so that the notation has
  a home a reader can look up.

- **The symbol $\iota$ is used in this library for other canonical maps, and this
  definition does not govern them.** It also denotes the canonical field
  embedding $\iota : \mathbb{Q} \to F$ ([[lem-of-q-embeds]]), the isometric
  embedding of a metric space into a completion ([[def-metric-completion]]), and
  an inclusion map $\iota : S \to X$ of a subspace. Each of those is introduced
  where it is used and means something different from the map defined here. What
  the four share is only that each is the canonical map of its situation.

- **Fields, not just ordered fields.** The recursion needs no order, so the
  definition is stated for a field; every use in this library is in an ordered
  field, and the order is what makes $\iota$ injective
  ([[lem-of-naturals-positive]]). In a field of positive characteristic $\iota$
  is not injective, which is one reason the injectivity is a lemma rather than
  part of the definition.
````

### `def-euclidean-inner-product`

````markdown
---
id: def-euclidean-inner-product
kind: definition
title: "The Euclidean inner product $\\langle x,y\\rangle = \\sum_{k<n} x_k y_k$ on $\\mathbb{R}^n$"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [def-norm-and-normed-space, def-function-space, def-vector-space, lem-standard-basis-of-f-n, def-finite-sum, lem-finite-sum-laws, lem-metrics-on-rn, lem-of-square-positive, thm-of-square-roots, def-natural-numbers, lem-nat-order-is-membership, def-integer-power, lem-power-laws]
justified_by: []
aliases: []
landmark: false
verification:
  precheck: n/a
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-28
  audited: 2026-07-29
sources:
  scraped: []
  references:
    - title: "Dot product (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Dot_product"
    - title: "Euclidean space (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Euclidean_space"
    - title: "J. Demmel, MA221 Lecture 3: Vector Norms"
      url: "https://people.eecs.berkeley.edu/~demmel/ma221_Fall10/Lectures/Lecture_03.html"
    - title: "G. Zitelli, Math 641 Functional Analysis, Part I"
      url: "https://www.math.uci.edu/~gzitelli/pdf/641/641part1.pdf"
pipeline_run: null
---

## Definition

Let $n \in \mathbb{N}$. A natural number is a von Neumann natural, that is a set,
and $n = \{0, 1, \dots, n-1\}$ ([[def-natural-numbers]],
[[lem-nat-order-is-membership]]), so

$$\mathbb{R}^{n} \;=\; \{\, x \;:\; x \text{ is a function } n \to \mathbb{R} \,\}$$

is the function space of [[def-function-space]] at $F = \mathbb{R}$ and $X = n$,
a vector space over $\mathbb{R}$ under the pointwise operations
([[def-vector-space]]). We write $x_k := x(k)$ for $k < n$, and two elements of
$\mathbb{R}^{n}$ are equal exactly when they agree at every $k < n$. This is the
same set that [[lem-metrics-on-rn]] calls $\mathbb{R}^{n}$.

The **Euclidean inner product** of $x, y \in \mathbb{R}^{n}$ is the real number

$$\langle x, y\rangle \;:=\; \sum_{k<n} x_k\,y_k ,$$

the finite sum of [[def-finite-sum]] applied to the list $k \mapsto x_k y_k$
(extended by $0$ beyond $n$, as every finite list in this library is). The
**Euclidean norm** of $x$ is

$$\lVert x\rVert_2 \;:=\; \sqrt{\langle x, x\rangle},$$

which is defined because $\langle x,x\rangle = \sum_{k<n} x_k^{2} \ge 0$ (a sum
of nonnegative terms, [[lem-finite-sum-laws]] clause 4 and
[[lem-of-square-positive]], the case $x_k = 0$ giving $x_k^2 = 0$ by
[[def-integer-power]]) and every nonnegative real has a unique nonnegative square
root ([[thm-of-square-roots]]).

### Both are defined for every $n$, including $n = 0$

At $n = 0$ the set $\mathbb{R}^{0}$ has exactly one element, the empty function,
and it is the zero vector space ([[lem-standard-basis-of-f-n]] clause 5); the sum
above is the empty sum, so $\langle x,y\rangle = 0$ and $\lVert x\rVert_2 = 0$.
**This is the first place on this page where the two index regimes diverge, and
the divergence is deliberate.** The published metrics $d_1$, $d_2$, $d_\infty$ of
[[lem-metrics-on-rn]] are defined only for $n \ge 1$, because $d_\infty$ would
otherwise be a maximum over the empty index set; the algebra above needs no such
restriction. The boundary in this page runs between the algebra and the metric,
not where a reader would guess, and [[rem-rn-conventions-and-scope]] lists
exactly which items inherit $n \ge 1$.

### The algebra of the inner product

For all $x, y, z \in \mathbb{R}^{n}$ and $\lambda \in \mathbb{R}$:

1. **Symmetry.** $\langle x,y\rangle = \langle y,x\rangle$, since $x_ky_k = y_kx_k$
   termwise.
2. **Additivity in the first argument.**
   $\langle x + y, z\rangle = \langle x,z\rangle + \langle y,z\rangle$: the list
   $k \mapsto (x_k+y_k)z_k$ is the termwise sum of $k \mapsto x_kz_k$ and
   $k \mapsto y_kz_k$, so [[lem-finite-sum-laws]] clause 1 applies.
3. **Homogeneity in the first argument.**
   $\langle \lambda x, y\rangle = \lambda\langle x,y\rangle$, by
   [[lem-finite-sum-laws]] clause 2.
4. **Bilinearity.** Clauses 2 and 3 together with symmetry give the same two laws
   in the second argument.
5. **Positive definiteness.** $\langle x,x\rangle \ge 0$, and
   $\langle x,x\rangle = 0$ if and only if $x = 0$. Indeed a vanishing sum of
   nonnegative terms has every term $0$ ([[lem-finite-sum-laws]] clause 4), so
   $x_k^{2} = 0$ for every $k < n$, and a nonzero real has a positive square
   ([[lem-of-square-positive]]), whence $x_k = 0$ for every $k < n$ and $x = 0$.
6. **Agreement with the published Euclidean metric.** For $n \ge 1$ and
   $x, y \in \mathbb{R}^{n}$,
   $\lVert x - y\rVert_2 = \sqrt{\sum_{k<n}(x_k-y_k)^{2}} = d_2(x,y)$, the two
   sides being the same expression ([[lem-metrics-on-rn]]). In particular
   $\lVert x\rVert_2 = d_2(x, 0)$.

That $\lVert\cdot\rVert_2$ is a norm in the sense of [[def-norm-and-normed-space]]
is proved in [[thm-cauchy-schwarz-and-the-euclidean-norm]], where the triangle
inequality is obtained from the Cauchy-Schwarz inequality; it is not assumed
here.

## Remarks

- **Scope: the concrete form only.** What is defined above is the Euclidean inner
  product on $\mathbb{R}^{n}$ and nothing more. The general theory of inner
  product spaces — abstract inner products, orthonormal bases, Gram-Schmidt,
  orthogonal projection and orthogonal complements of arbitrary subspaces — is
  planned for a page of this library that comes **earlier in the plan order** and
  is not yet built. No item on this page claims anything about abstract inner
  product spaces, and no item on this page introduces the general notion.

- **The standard basis and coordinates.** For $i < n$ the standard unit vector
  $e_i \in \mathbb{R}^{n}$ has $e_i(i) = 1$ and $e_i(j) = 0$ for $j \ne i$
  ([[lem-standard-basis-of-f-n]]). Then $\langle x, e_i\rangle = x_i$: the list
  $k \mapsto x_k (e_i)_k$ vanishes except at $k = i$, where its value is $x_i$,
  and a list vanishing off one index sums to its value there
  ([[lem-finite-sum-laws]] clause 3, splitting the range at $i$). So the
  coordinates of $x$ are recovered by testing against the standard basis, which
  is the form used repeatedly below.

- **Powers here are integer powers.** $x_k^{2}$ means the integer power of
  [[def-integer-power]], and $\lVert x\rVert_2^{2} = \langle x,x\rangle$ by
  [[thm-of-square-roots]] and [[lem-power-laws]].
````

### `def-injection-surjection-bijection`

````markdown
---
id: def-injection-surjection-bijection
kind: definition
title: "Injection, surjection, bijection"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [def-function, def-image-and-preimage-under-a-relation]
justified_by: []
aliases: [def-injective, def-surjective, def-bijective]
landmark: false
short: "injective, surjective, bijective"
verification:
  precheck: n/a
  verified:
    model: claude-opus-5
    verdict: certify
    date: 2026-08-06
    scope: published-rehoming-repair
    delegated_by: owner
sources:
  scraped: []
  references:
    - title: "J. K. Hunter, An Introduction to Real Analysis"
      url: "https://www.math.ucdavis.edu/~hunter/intro_analysis_pdf/intro_analysis.pdf"
    - title: "J. Lebl, Basic Analysis: Introduction to Real Analysis, basic set theory"
      url: "https://www.jirka.org/ra/html/sec_basicset.html"
    - title: "Bijection, injection and surjection (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Bijection,_injection_and_surjection"
    - title: "T. Tao, Analysis I, 3rd ed., §3.3 (Functions)"
      url: "https://terrytao.wordpress.com/books/analysis-i/"
pipeline_run: null
---

## Definition

Let $A$ and $B$ be sets and let $f : A \to B$ be a function ([[def-function]]).

- $f$ is **injective** (one-to-one) if $f(x) = f(y)$ implies $x = y$, for all
  $x, y \in A$.
- $f$ is **surjective** (onto) if for every $b \in B$ there is some $x \in A$
  with $f(x) = b$; equivalently, the image $f[A] := \{ f(x) : x \in A \}$ equals
  $B$.
- $f$ is **bijective** if it is both injective and surjective.

For $S \subseteq A$ we write $f[S] = \{ f(x) : x \in S \}$ for the image of $S$,
and for $T \subseteq B$ we write $f^{-1}[T] = \{ x \in A : f(x) \in T \}$ for the
preimage of $T$; these are the image and preimage of a set under $f$ read as a
relation ([[def-image-and-preimage-under-a-relation]]).

## Remarks

- **Composition.** If $f : A \to B$ and $g : B \to C$ are both injective then so
  is $g \circ f$, since $g(f(x)) = g(f(y))$ forces $f(x) = f(y)$ and then
  $x = y$; if both are surjective then so is $g \circ f$, since any $c \in C$ is
  $g(b)$ for some $b \in B$ and that $b$ is $f(a)$ for some $a \in A$. Hence a
  composition of bijections is a bijection. These verifications, together with the
  two partial converses, are
  [[prop-composition-preserves-injectivity-surjectivity-and-bijectivity]].

- **Inverses.** $f : A \to B$ is bijective exactly when there is a function
  $f^{-1} : B \to A$ with $f^{-1}(f(x)) = x$ for all $x \in A$ and
  $f(f^{-1}(b)) = b$ for all $b \in B$; that two-sided inverse is unique, and it
  is itself a bijection. Injectivity alone gives a bijection from $A$ onto the
  image $f[A]$, and hence an inverse defined on $f[A]$ only. No choice principle
  is involved: the value $f^{-1}(b)$ is the *unique* $x$ with $f(x) = b$, so it
  is determined rather than selected. The full statement, with the uniqueness of the
  two-sided inverse, is
  [[thm-a-function-is-a-bijection-exactly-when-it-has-a-two-sided-inverse]]; the
  corresponding statement for an arbitrary surjection is not available at this point
  in the reading order, because a right inverse for every surjection is equivalent
  to the Axiom of Choice.

- **What this item does and does not do.** A function $A \to B$ is a set of ordered
  pairs, single valued and total on $A$ ([[def-function]]); ordered pairs, Cartesian
  products, images and preimages are fixed by [[def-ordered-pair]],
  [[def-cartesian-product]] and [[def-image-and-preimage-under-a-relation]]. This
  item only fixes the three adjectives and the notation used for them. Nothing here
  is proved.
````

### `def-integer-power`

````markdown
---
id: def-integer-power
kind: definition
title: "Integer powers $a^m$"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [thm-recursion, def-ordered-field, def-integers, def-field, def-int-operations, lem-nat-embeds-int, lem-of-inverse-unique, lem-of-no-zero-divisors, lem-of-zero-mult, thm-int-ordered-ring]
justified_by: [lem-power-laws]
aliases: [def-power]
landmark: false
verification:
  precheck: n/a
  verified:
    model: claude-opus-5
    verdict: certify
    date: 2026-07-26
    scope: page
    delegated_by: owner
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-25
sources:
  scraped: []
  references:
    - title: "J. Aspnes, Summation Notation"
      url: "https://www.cs.yale.edu/homes/aspnes/pinewiki/SummationNotation.html"
    - title: "M. Fochler, Recursive sums, products, and powers"
      url: "https://people.math.binghamton.edu/mfochler/bu-mfx/bu-math-arv/math-330-arv/math-330-2019-08/html/lec-notes/bu-ln-330-m330-solns-2019-12-03.pdf"
    - title: "Exponentiation (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Exponentiation"
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 1"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "T. Tao, Analysis I, 3rd ed., §4.3"
      url: "https://terrytao.wordpress.com/books/analysis-i/"
pipeline_run: null
---

## Definition

Let $a \in \mathbb{R}$, where $\mathbb{R}$ is the ambient ordered field
([[def-ordered-field]], [[def-field]]).

**Natural exponents.** By the recursion theorem ([[thm-recursion]]) applied to
the set $\mathbb{R}$, the starting element $1$ and the function
$f(x) = x \cdot a$, there is a unique function $\mathbb{N} \to \mathbb{R}$,
written $n \mapsto a^n$, with

$$a^0 = 1, \qquad a^{n+1} = a^n \cdot a \quad (n \in \mathbb{N}).$$

Thus $a^1 = a$, $a^2 = a \cdot a$, and so on. Note that this is defined for
**every** $a$, including $a = 0$.

**Negative exponents.** If $a \ne 0$ and $n \in \mathbb{N}$ with $n \ge 1$, set

$$a^{-n} := (a^n)^{-1}.$$

**Why that is legitimate.** The right-hand side presupposes that $a^n$ is
invertible, that is, that $a^n \ne 0$. This is a proof obligation and not an
observation, and it is discharged by claim 2 of [[lem-power-laws]]: for $a \ne 0$
in a field, $a^n \ne 0$ for every $n \in \mathbb{N}$, proved there by induction on
$n$ from the fact that a field has no zero divisors ([[lem-of-no-zero-divisors]]).
That lemma is a statement *about* the operation introduced here, so it depends on
this definition and is recorded in this item's `justified_by` rather than in its
`deps` (SCHEMA §3). Given $a^n \ne 0$, the value $(a^n)^{-1}$ is a single
well-determined element, because multiplicative inverses in a field are unique
([[lem-of-inverse-unique]]).

**Integer exponents.** Every integer $m$ ([[def-integers]]) is either
$\iota(n)$ or $-\iota(n)$ for a unique natural $n$, where $\iota$ is the
embedding $\mathbb{N} \to \mathbb{Z}$ ([[lem-nat-embeds-int]],
[[def-int-operations]]). This too is a citation and not a slogan: the order on
$\mathbb{Z}$ is total ([[thm-int-ordered-ring]]), so $m \ge 0$ or $m < 0$; the
image of $\iota$ is exactly the set of nonnegative integers, and each of them is
$\iota(n)$ for a unique natural $n$ ([[lem-nat-embeds-int]]); and if $m < 0$ then
$-m > 0$, by compatibility of the order with addition ([[thm-int-ordered-ring]]),
so $-m = \iota(n)$ and $m = -\iota(n)$, with $n$ unique because $\iota$ is
injective. The two clauses above therefore define $a^m$ for every
$m \in \mathbb{Z}$ whenever $a \ne 0$, and for every $m \in \mathbb{N}$ for
arbitrary $a$. The clauses are consistent where they overlap: the only overlap is
$m = 0$, where $-\iota(0) = \iota(0)$ and $(a^0)^{-1} = 1^{-1} = 1 = a^0$.

## Remarks

- **The convention $0^0 = 1$ is adopted here**, and it is not a matter of taste
  but of agreement with the recursion above: $a^0 = 1$ is the starting value for
  every $a$, exactly as the empty product is $1$ ([[def-finite-sum]]). This is
  the convention that makes the empty product, the binomial theorem, and
  polynomial notation $\sum_k c_k x^k$ work at $x = 0$ without an exception. The
  competing convention "$0^0$ undefined" belongs to contexts where $x^y$ is
  studied as a function of two *real* variables and one wants continuity, which
  is unavailable and irrelevant here: the exponent in $a^m$ is an integer, never
  a real.
- $0^n = 0$ for every $n \ge 1$, since $0^{n} = 0^{n-1} \cdot 0 = 0$, a product
  with a zero factor ([[lem-of-zero-mult]]); and
  $0^{-n}$ is not defined for $n \ge 1$, since $0$ has no inverse.
- The exponent is an integer and stays an integer. Rational exponents are a
  separate construction resting on the existence of roots
  ([[thm-nth-roots-exist]], [[def-rational-power]]), and real exponents do not
  exist in this library yet ([[rem-real-exponents-deferred]]).
- The laws $a^{m+n} = a^m a^n$, $(a^m)^n = a^{mn}$ and $(ab)^n = a^n b^n$ are
  proved, not assumed, in [[lem-power-laws]]; the order behaviour of $a \mapsto a^n$
  is [[lem-power-monotone]].
````

### `def-linear-subspace`

````markdown
---
id: def-linear-subspace
kind: definition
title: "Linear subspace of a vector space"
status: published
origin: session
provenance:
  statement: literature-derived
  proof: ai-altered
deps: [def-vector-space, def-subgroup, def-group, lem-vector-space-elementary-consequences]
justified_by: []
aliases: [def-linear-subspace-of-a-vector-space]
landmark: true
short: "linear subspace $W \\le V$"
verification:
  precheck: n/a
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-28
  audited: 2026-07-28
sources:
  scraped: []
  references:
    - title: "Linear subspace (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Linear_subspace"
    - title: "S. Axler, Linear Algebra Done Right, 4th ed., Ch. 1"
      url: "https://linear.axler.net/"
pipeline_run: null
---

## Definition

Let $V$ be a vector space over a field $F$ ([[def-vector-space]]). A subset
$W \subseteq V$ is a **linear subspace** of $V$ when

- **(W1)** $0_V \in W$;
- **(W2)** $W$ is closed under the vector addition: $u, v \in W$ implies
  $u + v \in W$;
- **(W3)** $W$ is closed under scalar multiplication: $\lambda \in F$ and
  $v \in W$ imply $\lambda v \in W$.

Every vector space $V$ has the two **trivial linear subspaces** $\{0_V\}$ and $V$
itself; a linear subspace $W$ with $W \ne V$ is called **proper**.

**The restricted operations are the required data, and $W$ is a vector space.**
By (W2) the vector addition of $V$ restricts to a binary operation
$W \times W \to W$, and by (W3) the scalar multiplication restricts to a map
$F \times W \to W$. With these and the element $0_V$, the set $W$ is a vector
space over $F$:

- axioms (V2)–(V5) are equations required of elements of $W$, which are in
  particular elements of $V$, so they are inherited from $V$; likewise
  associativity and commutativity of the restricted addition;
- $0_V$ lies in $W$ by (W1) and is a two-sided identity for the restricted
  addition, since it is one in $V$;
- for $v \in W$ the vector $(-1_F)v$ lies in $W$ by (W3), and
  $(-1_F)v = -v$ ([[lem-vector-space-elementary-consequences]]), so $-v \in W$
  and $v + (-v) = 0_V$ holds in $W$.

So $(W,+,0_V)$ is an abelian group, which is axiom (V1), and $W$ is a vector
space over $F$ **whose zero vector and whose additive inverses are those of
$V$**. In the language of [[def-subgroup]], the three displayed conditions
(S1) $0_V \in W$, (S2) closure under addition and (S3) closure under additive
inverses all hold, so $W$ is a subgroup of the abelian group $(V,+,0_V)$
([[def-group]]); that reading, and its converse, are recorded as
[[lem-linear-subspace-is-a-subgroup]] and are cited from there rather than
re-argued below.

## Remarks

- **"Linear subspace", never bare "subspace", in this library.** The word
  *subspace* is already in use here for the topological notion, a subset of a
  topological space carrying the induced topology, which is an unrelated idea.
  The names on this page therefore all say *linear*: `def-linear-subspace`,
  `lem-linear-subspace-criterion`, `lem-intersection-of-linear-subspaces`,
  `lem-linear-subspace-is-a-subgroup`, `def-sum-of-linear-subspaces`. Where the
  ambient vector space is fixed and no confusion is possible, the surrounding
  prose still writes the full phrase.

- **Closure under negatives is not a fourth condition.** It follows from (W3),
  because the additive inverse of a vector is the scalar multiple $(-1_F)v$. This
  is why the definition asks for three conditions where the definition of a
  subgroup asks for three of its own, and why the one-step test
  ([[lem-linear-subspace-criterion]]) can compress them into one.

- **(W1) cannot be replaced by "$W \ne \varnothing$" while dropping the others.**
  It can be replaced by nonemptiness *given* (W3), since a nonempty $W$ closed
  under scalar multiplication contains $0_F v = 0_V$
  ([[lem-vector-space-elementary-consequences]]) for any of its elements $v$.
  Stated with (W1) the definition is checkable one condition at a time, and the
  economical single test is [[lem-linear-subspace-criterion]].

- **The field matters.** A subset of $V$ may be closed under the scalars of a
  subfield $K \subseteq F$ without being closed under all of $F$, so "linear
  subspace" always means "linear subspace over the field named". Restriction of
  scalars ([[lem-restriction-of-scalars]]) is what makes that distinction
  possible.
````

### `def-monotone-sequence`

````markdown
---
id: def-monotone-sequence
kind: definition
title: "Nondecreasing, increasing, nonincreasing, decreasing, monotone, and eventually monotone sequences"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [def-sequence, def-real-order, def-complete-ordered-field, def-bounded-set, def-nat-order, thm-nat-linear-order, lem-nat-discrete, thm-induction-principle]
justified_by: []
aliases: []
landmark: true
verification:
  precheck: n/a
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-26
  audited: 2026-07-26
sources:
  scraped: []
  references:
    - title: "Monotonic function (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Monotonic_function"
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 3 (Def. 3.13)"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "T. Tao, Analysis I, 3rd ed., §6.3"
      url: "https://terrytao.wordpress.com/books/analysis-i/"
    - title: "J. Lebl, Basic Analysis I, §2.2"
      url: "https://www.jirka.org/ra/"
---

## Definition

Let $(x_k)$ be a sequence of reals ([[def-sequence]]), with $\mathbb{R}$ ordered
as in [[def-real-order]] and [[def-complete-ordered-field]], and with
$\mathbb{N}$ ordered as in [[def-nat-order]]. The sequence is:

- **nondecreasing** when $x_j \le x_k$ for all $j \le k$;
- **increasing** (or *strictly increasing*) when $x_j < x_k$ for all $j < k$;
- **nonincreasing** when $x_j \ge x_k$ for all $j \le k$;
- **decreasing** (or *strictly decreasing*) when $x_j > x_k$ for all $j < k$;
- **monotone** when it is nondecreasing or nonincreasing;
- **strictly monotone** when it is increasing or decreasing;
- **eventually monotone** when some tail $x^{(K)}$ ([[def-sequence]]) is
  monotone, that is when there is $K \in \mathbb{N}$ such that the restriction of
  the comparison to indices $\ge K$ is one-signed.

An increasing sequence is nondecreasing and a decreasing sequence is
nonincreasing, since $j \le k$ means $j < k$ or $j = k$ and the second case gives
equality. A sequence that is both nondecreasing and nonincreasing is constant.

**Consecutive comparisons suffice, and that is an induction.** The four
conditions above quantify over *all* pairs of indices, but what one checks in
practice, and what a recursive construction delivers, is the comparison of
consecutive terms. The two agree:

> $(x_k)$ is nondecreasing **if and only if** $x_k \le x_{\sigma(k)}$ for every
> $k \in \mathbb{N}$, and $(x_k)$ is increasing **if and only if**
> $x_k < x_{\sigma(k)}$ for every $k \in \mathbb{N}$; likewise, with the
> inequalities reversed, for nonincreasing and decreasing.

The forward implications are the instances $j = k$, $k = \sigma(k)$ of the
definitions, using $k < \sigma(k)$ ([[lem-nat-discrete]]). For the converse,
suppose $x_i \le x_{\sigma(i)}$ for every $i$ and fix $k$; we show by induction
on $k$ ([[thm-induction-principle]]) that $x_j \le x_k$ for every $j \le k$. For
$k = 0$: $j \le 0$ forces $j = 0$, and $x_0 \le x_0$. Assume the statement for
$k$ and let $j \le \sigma(k)$. If $j = \sigma(k)$ then $x_j \le x_{\sigma(k)}$ by
reflexivity. Otherwise $j < \sigma(k)$, and then $j \le k$: were $k < j$ we would
have $k < j < \sigma(k)$, which [[lem-nat-discrete]] excludes, so $j \le k$ by
totality of the order on $\mathbb{N}$ ([[thm-nat-linear-order]]). The induction
hypothesis gives $x_j \le x_k$, and $x_k \le x_{\sigma(k)}$ by assumption, so
$x_j \le x_{\sigma(k)}$ by transitivity. This completes the induction. The three
remaining equivalences are the same argument with $\le$ replaced by $<$,
$\ge$ or $>$, transitivity of the strict order being used in the same place.

**Boundedness of a monotone sequence is one-sided.** A nondecreasing sequence is
bounded below by its first term $x_0$, and a nonincreasing sequence is bounded
above by $x_0$, both immediately from the definition with $j = 0$. So for a
nondecreasing sequence the only substantive question is whether it is bounded
above, and for a nonincreasing sequence whether it is bounded below. The range of
$(x_k)$ is the set $\{x_k : k \in \mathbb{N}\}$ ([[def-sequence]]), and it is
bounded above, bounded below or bounded in the sense of [[def-bounded-set]]
exactly when the sequence is.

## Remarks

- **The naming is the one that keeps "increasing" strict.** Some texts use
  *increasing* for what is called *nondecreasing* here and *strictly increasing*
  for what is called *increasing*. This library follows the convention in which
  the unqualified word is strict, and always writes *nondecreasing* when
  equality is allowed, so that no statement on this page depends on which
  convention a reader arrives with. Where a proof needs the weak form it says
  *nondecreasing*, and where it needs the strict form it says *increasing*.

- **Eventual monotonicity is exactly monotonicity of a tail**, and by
  [[lem-limit-of-tail]] a sequence and its tails converge to the same limits and
  are Cauchy together. So every convergence statement about monotone sequences on
  this page extends verbatim to eventually monotone sequences, with the limit
  unchanged; only statements about specific terms, such as the identification of
  the limit as the supremum of the *whole* range, need the hypothesis at every
  index. The monotone convergence theorem is a case in point: an eventually
  nondecreasing bounded sequence converges, but to the supremum of the range of
  the monotone tail, which may be smaller than the supremum of the whole range.

- **Monotone is strictly weaker than strictly monotone, and neither is generic.**
  A constant sequence is monotone and not strictly monotone; the sequence with
  terms $1$ and $-1$ alternating ([[lem-alternating-sequence]]) is not monotone
  and not eventually monotone, since every tail contains both values infinitely
  often. That sequence is bounded, so boundedness alone gives neither form of
  monotonicity; what it does give is a monotone *subsequence*
  ([[lem-peak-monotone-subsequence]]), and that is the route to
  Bolzano-Weierstrass.
````

### `def-norm-and-normed-space`

````markdown
---
id: def-norm-and-normed-space
kind: definition
title: "A norm on a real vector space, the induced metric, and the dictionary with the metric axioms"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [def-vector-space, def-function-space, def-linear-map, def-metric-space, lem-metric-nonnegativity, def-metric-topology, lem-bounded-remetrisation, rem-metric-axiom-conventions, def-abs-value, lem-of-abs-value, lem-of-triangle-inequality, def-complete-ordered-field, lem-vector-space-elementary-consequences]
justified_by: []
aliases: []
landmark: true
verification:
  precheck: n/a
sources:
  scraped: []
  references:
    - title: "Norm (mathematics) (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Norm_(mathematics)"
    - title: "Normed vector space (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Normed_vector_space"
    - title: "J. Demmel, MA221 Lecture 3: Vector Norms"
      url: "https://people.eecs.berkeley.edu/~demmel/ma221_Fall10/Lectures/Lecture_03.html"
    - title: "G. Zitelli, Math 641 Functional Analysis, Part I"
      url: "https://www.math.uci.edu/~gzitelli/pdf/641/641part1.pdf"
pipeline_run: null
---

## Definition

Throughout this page $\mathbb{R}$ is the complete ordered field
([[def-complete-ordered-field]]) constructed in this library, in particular a
field, so that "vector space" below always means vector space over $\mathbb{R}$
([[def-vector-space]]).

Let $V$ be a vector space over $\mathbb{R}$, with zero vector $0_V$. A **norm on
$V$** is a function $N : V \to \mathbb{R}$ such that for all $u, v \in V$ and all
$\lambda \in \mathbb{R}$:

- **(N1) Separation.** $N(v) = 0$ if and only if $v = 0_V$.
- **(N2) Absolute homogeneity.** $N(\lambda v) = |\lambda|\,N(v)$, the absolute
  value being that of [[def-abs-value]].
- **(N3) Triangle inequality.** $N(u + v) \le N(u) + N(v)$.

A **normed space** is a pair $(V, N)$ consisting of a vector space $V$ over
$\mathbb{R}$ and a norm $N$ on it. When only one norm is in play we write
$\lVert v\rVert$ for $N(v)$; when several are, the norm is always named.

**The values of a norm are real numbers.** The codomain is $\mathbb{R}$, so
$N(v)$ is an honest element of the complete ordered field and no infinite value
is permitted. This is the same convention [[rem-metric-axiom-conventions]]
records for metrics.

### Nonnegativity is a theorem, not an axiom

Many texts add a fourth condition $N(v) \ge 0$. It is redundant. Applying (N2)
with $\lambda = -1$ gives $N(-v) = |-1|\,N(v) = N(v)$ ([[lem-of-abs-value]],
[[lem-vector-space-elementary-consequences]] for $(-1)v = -v$), and then (N3)
with $u = v$ and $-v$ gives

$$0 \;=\; N(0_V) \;=\; N\bigl(v + (-v)\bigr) \;\le\; N(v) + N(-v) \;=\; N(v) + N(v),$$

where $N(0_V) = 0$ is (N1). So $N(v) + N(v) \ge 0$, and if $N(v) < 0$ then
$N(v) + N(v) < 0$ by addition of inequalities, which trichotomy forbids
([[def-complete-ordered-field]]). Hence $N(v) \ge 0$ for every $v \in V$.

**Consequently the verification of a candidate norm has three things to check and
not four**, exactly as the verification of a candidate metric has three and not
four ([[def-metric-space]], [[lem-metric-nonnegativity]]). No item in this
library assumes nonnegativity of a norm before the argument above.

### The induced metric

Let $N$ be a norm on $V$ and define

$$d_N(u,v) \;:=\; N(u - v) \qquad (u, v \in V),$$

where $u - v = u + (-v)$ ([[def-vector-space]]). **Then $d_N$ is a metric on
$V$** ([[def-metric-space]]), and the three axioms are the three conditions
above, in order:

- **(M1)** $d_N(u,v) = 0$ means $N(u-v) = 0$, which by (N1) says $u - v = 0_V$,
  that is $u = v$; and conversely $d_N(v,v) = N(0_V) = 0$.
- **(M2)** $d_N(v,u) = N(v-u) = N\bigl((-1)(u-v)\bigr) = |-1|\,N(u-v) = d_N(u,v)$,
  by (N2), [[lem-of-abs-value]] and $(-1)w = -w$
  ([[lem-vector-space-elementary-consequences]]).
- **(M3)** $d_N(u,w) = N\bigl((u-v) + (v-w)\bigr) \le N(u-v) + N(v-w) = d_N(u,v) + d_N(v,w)$,
  by (N3).

A normed space is therefore a metric space, and every notion defined for metric
spaces — open set ([[def-metric-topology]]), convergence, Cauchyness,
continuity, compactness — is available in it with no further definition. **This
library never introduces a second notion of any of them for normed spaces.**

### Two properties an arbitrary metric need not have

The metric $d_N$ satisfies, for all $u, v, w \in V$ and $\lambda \in \mathbb{R}$:

- **translation invariance**, $d_N(u + w, v + w) = N\bigl((u+w)-(v+w)\bigr) = N(u-v) = d_N(u,v)$;
- **absolute homogeneity**, $d_N(\lambda u, \lambda v) = N\bigl(\lambda(u-v)\bigr) = |\lambda|\,d_N(u,v)$, by (N2).

**Not every metric on a vector space arises from a norm**, and homogeneity is
what fails. The published bounded remetrisation [[lem-bounded-remetrisation]]
replaces a metric $d$ by $d' = \min\{d, 1\}$, a metric with the same topology
whose values never exceed $1$; on a vector space $V$ containing a vector $v$ with
$d(v, 0_V) > 0$ this $d'$ cannot be $d_M$ for any norm $M$, since absolute
homogeneity would force $d'(\lambda v, 0_V) = |\lambda|\,d'(v, 0_V)$, which is
unbounded in $\lambda$, while $d'$ is bounded by $1$. So the passage from norms
to metrics is not reversible, and a statement about a metric on a vector space is
strictly weaker than the corresponding statement about a norm.

## Remarks

- **Why (N1) is stated as an equivalence.** The direction $N(0_V) = 0$ is forced
  by (N2) with $\lambda = 0$, since $0\,v = 0_V$
  ([[lem-vector-space-elementary-consequences]]) gives $N(0_V) = |0|\,N(v) = 0$.
  Only the direction "$N(v) = 0$ implies $v = 0_V$" is a genuine assumption, and
  dropping it gives what is usually called a seminorm, a notion this library does
  not use. The situation is exactly the one [[rem-metric-axiom-conventions]]
  describes for (M1) and the pseudometric.

- **The zero space carries exactly one norm.** If $V = \{0_V\}$ then the only
  function $V \to \mathbb{R}$ satisfying (N1) is the one with value $0$, and it
  satisfies (N2) and (N3) trivially. In particular $\mathbb{R}^{0}$, the function
  space on the empty index set ([[def-function-space]]), is a normed space,
  although the metrics of the published metric theory on $\mathbb{R}^n$ are
  defined only for $n \ge 1$.

- **What is not defined here.** This item does not define linear maps; their
  published definition is [[def-linear-map]]. It also does not define operator
  norms, dual spaces, or abstract inner product spaces.
  [[rem-rn-conventions-and-scope]] records the remaining scope boundaries and
  what each later development would license.
````

### `def-p-norms-on-rn`

````markdown
---
id: def-p-norms-on-rn
kind: definition
title: "The $p$-norms $\\lVert x\\rVert_p$ for rational $p \\ge 1$, and $\\lVert x\\rVert_\\infty$"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [def-norm-and-normed-space, def-euclidean-inner-product, def-rational-power, lem-rational-power-well-defined, lem-rational-power-laws, lem-rational-power-monotone, rem-real-exponents-deferred, thm-minkowski-finite, def-finite-sum, lem-finite-sum-laws, lem-finite-set-has-max, def-max-min, lem-metrics-on-rn, def-abs-value, lem-of-abs-value, thm-of-square-roots]
justified_by: []
aliases: []
landmark: false
verification:
  precheck: n/a
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-28
  audited: 2026-07-29
sources:
  scraped: []
  references:
    - title: "Lp space (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Lp_space"
    - title: "Norm (mathematics) (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Norm_(mathematics)"
    - title: "J. Demmel, MA221 Lecture 3: Vector Norms"
      url: "https://people.eecs.berkeley.edu/~demmel/ma221_Fall10/Lectures/Lecture_03.html"
    - title: "G. Zitelli, Math 641 Functional Analysis, Part I"
      url: "https://www.math.uci.edu/~gzitelli/pdf/641/641part1.pdf"
pipeline_run: null
---

## Definition

Let $n \in \mathbb{N}$ and let $\mathbb{R}^{n}$ be the function space of
[[def-euclidean-inner-product]], with $x_k := x(k)$ for $k < n$.

### The $p$-norm, for a rational exponent $p \ge 1$

Let $p \in \mathbb{Q}$ with $p \ge 1$. For $x \in \mathbb{R}^{n}$ put

$$\lVert x\rVert_p \;:=\; \Bigl(\sum_{k<n} |x_k|^{p}\Bigr)^{1/p},$$

where $|\cdot|$ is the absolute value ([[def-abs-value]]), the sum is the finite
sum of [[def-finite-sum]], and both powers are the **rational** powers of
[[def-rational-power]].

**Every power written here is defined.** Each base $|x_k|$ is a nonnegative real
and $p > 0$, so $|x_k|^{p}$ is given by [[def-rational-power]] for $|x_k| > 0$
and by its supplementary clause $0^{p} = 0$ for $|x_k| = 0$; the sum of these
nonnegative terms is nonnegative ([[lem-finite-sum-laws]] clause 4), and
$1/p$ is a positive rational, so the outer power is defined for the same two
reasons. The value does not depend on which representative of $p$ or of $1/p$ is
used ([[lem-rational-power-well-defined]]).

**The exponent is a rational, and that is not a matter of taste.**
[[def-rational-power]] supplies $a^{r}$ for a nonnegative base and a **rational**
exponent only; real exponents do not exist at this point in the reading order,
and [[rem-real-exponents-deferred]] records exactly why. This is also why the
published Minkowski inequality [[thm-minkowski-finite]], which is what makes the
triangle inequality work below, is itself stated for rational $p \ge 1$. **No
statement on this page is written for $p$ ranging over a real interval.**

### The maximum norm

For $n \ge 1$ and $x \in \mathbb{R}^{n}$ put

$$\lVert x\rVert_\infty \;:=\; \max\{\, |x_k| \;:\; k < n \,\},$$

the maximum of a nonempty finite set of reals, which exists and is one of its
elements ([[lem-finite-set-has-max]], [[def-max-min]]).

**The hypothesis $n \ge 1$ is required and propagates.** At $n = 0$ the set
$\{|x_k| : k<n\}$ is empty and has no maximum ([[def-max-min]]). This is the same
restriction the published [[lem-metrics-on-rn]] carries, for the same reason, and
**every statement on this page that mentions $\lVert\cdot\rVert_\infty$ inherits
it**. The $p$-norms for rational $p \ge 1$ carry no such restriction: at $n = 0$
each is the empty sum raised to a positive rational power, hence $0$.

### The three cases the rest of the page uses

- $\lVert x\rVert_1 = \sum_{k<n}|x_k|$, since $t^{1} = t$ for $t \ge 0$
  ([[lem-rational-power-laws]], and $0^{1} = 0$ by the supplementary clause).
- $\lVert x\rVert_2 = \bigl(\sum_{k<n}|x_k|^{2}\bigr)^{1/2} = \sqrt{\sum_{k<n}x_k^{2}}$,
  which is exactly the Euclidean norm of [[def-euclidean-inner-product]]: the
  exponent $2$ agrees with the integer power, so $|x_k|^{2} = x_k^{2}$
  ([[lem-of-abs-value]]), and $t^{1/2}$ is the unique nonnegative square root of
  $t$, which is $\sqrt{t}$ ([[def-rational-power]], [[thm-of-square-roots]]).
  **The two notations denote the same function and no second Euclidean norm is
  introduced.**
- $\lVert x\rVert_\infty$ as above, for $n \ge 1$.

That each of these is a norm in the sense of [[def-norm-and-normed-space]], and
that the metrics they induce are exactly the published $d_1$, $d_2$ and
$d_\infty$ of [[lem-metrics-on-rn]], is
[[lem-p-norms-are-norms-and-induce-the-published-metrics]]; it is proved there
and is not assumed here.

## Remarks

- **Why $p \ge 1$.** The triangle inequality for $\lVert\cdot\rVert_p$ is
  Minkowski's inequality, and [[thm-minkowski-finite]] is stated for rational
  $p \ge 1$. For $0 < p < 1$ the displayed expression is still defined but is not
  a norm on $\mathbb{R}^{n}$ for $n \ge 2$; nothing on this page asserts anything
  about that range, and the expression is never written with such an exponent.

- **Monotonicity in the base is what makes the comparisons below work.** For a
  fixed positive rational $r$ the map $a \mapsto a^{r}$ is strictly increasing on
  the positive reals ([[lem-rational-power-monotone]] clause 2), so an inequality
  between nonnegative sums passes through the outer power. That is the only
  property of rational powers used in the comparison chain of
  [[lem-every-norm-on-rn-is-continuous-for-the-euclidean-metric]].

- **The subscript $\infty$ is a name, not a number.** No arithmetic is performed
  with it, and $\lVert\cdot\rVert_\infty$ is not $\lVert\cdot\rVert_p$ for any
  exponent; it is a separately defined function that happens to sit at the end of
  the family. This is the same refusal to extend $\mathbb{R}$ silently that
  [[def-interval]] records for the interval notation.
````

### `def-rational-power`

````markdown
---
id: def-rational-power
kind: definition
title: "Rational powers $a^r$ of a positive base"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [thm-nth-roots-exist, def-integer-power, def-rationals, lem-rat-positive-denominator, lem-nat-embeds-int, def-rat-order, lem-power-monotone, lem-power-laws, lem-of-inverse-positive]
justified_by: [lem-rational-power-well-defined]
aliases: []
landmark: true
short: "$a^{m/n} := (a^{1/n})^m$, $a>0$"
verification:
  precheck: n/a
  judge:
    model: "deepseek-v4-pro + gpt-5.6-terra"
    verdict: pass
    date: 2026-08-04
    scope: published-audit-targeted
    context_sha256: 22067f1978d2f781dd7327a6f5c81cccbbc2009bd13885930f7d56ba5a2ceb5e
    item_sha256: 4f75fe6e8c39549d9a1c82a4fc920d13b890d3917b367621daddcaf70f377565
  verified:
    model: gpt-5.6-sol-codex-subscription
    verdict: certify
    date: 2026-08-04
    scope: published-audit
    delegated_by: owner
sources:
  scraped: []
  references:
    - title: "J. Lebl, Basic Analysis I"
      url: "https://www.jirka.org/ra/realanal.pdf"
    - title: "Radicals and rational exponents (Emory University)"
      url: "https://mathcenter.oxford.emory.edu/site/math100/radicals/"
    - title: "Exponentiation (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Exponentiation"
    - title: "Nth root (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Nth_root"
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 1"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
pipeline_run: null
---

## Definition

Let $a \in \mathbb{R}$ with $a > 0$ and let $r \in \mathbb{Q}$ ([[def-rationals]]).

Every rational has a representative with positive denominator
([[lem-rat-positive-denominator]]), so write $r = m/n$ with $m \in \mathbb{Z}$
and $n$ a positive integer; a positive integer is the image of a unique natural
$\ge 1$ ([[lem-nat-embeds-int]]), and we write $n$ for that natural too. Define

$$a^{r} := \big(a^{1/n}\big)^{m},$$

where $a^{1/n}$ is the unique nonnegative $n$-th root of $a$
([[thm-nth-roots-exist]]) and the outer exponent is an integer power
([[def-integer-power]]). The outer power is legitimate because $a^{1/n} > 0$ when
$a > 0$, so it has an inverse and negative integer exponents are allowed.

**Well-definedness.** The right-hand side must not depend on which representative
$m/n$ of $r$ was chosen. It does not: that is [[lem-rational-power-well-defined]],
which is recorded in this item's `justified_by` rather than in its `deps`, since
it is a statement *about* the operation defined here and therefore depends on
this definition.

**The base must be positive.** For $a < 0$ the same formula is not a definition
at all, because different representatives of the same rational give different
answers, or no answer: see [[fs-rational-power-of-negative-base]], which is
exactly the item that justifies the restriction.

**Supplementary clause for the base $0$.** For $a = 0$ and rational $r > 0$
([[def-rat-order]]) the displayed formula still makes sense and still does not
depend on the representative: $r > 0$ forces $m \ge 1$, and
$\big(0^{1/n}\big)^{m} = 0^{m} = 0$ ([[thm-nth-roots-exist]] applies to every
$a \ge 0$). So we set $0^{r} = 0$ for rational $r > 0$. For $r < 0$ the
expression $0^{r}$ is left undefined, since $0$ has no inverse. This clause is
what lets the inequalities later on this page be stated for nonnegative entries
rather than for positive ones only.

## Remarks

- **Consistency with integer powers.** If $r \in \mathbb{Z}$ then $r = r/1$,
  $a^{1/1} = a$ ([[thm-nth-roots-exist]]), and the definition returns
  $(a^{1})^{r} = a^{r}$ as given by [[def-integer-power]]. So the notation $a^{r}$
  is unambiguous, and rational powers extend integer powers on positive bases.
  At $r = 1/n$ it returns $\big(a^{1/n}\big)^{1} = a^{1/n}$, so the root notation
  of [[thm-nth-roots-exist]] is the special case $r = 1/n$, as intended.
- $a^{r} > 0$ for every $a > 0$ and **every** $r \in \mathbb{Q}$, the exponent $0$
  included. Writing $r = m/n$ with $n \ge 1$: the root $a^{1/n}$ is positive
  ([[thm-nth-roots-exist]]); for $m \ge 0$ the value $\big(a^{1/n}\big)^{m}$ is a
  natural power of a positive element, hence positive, which is claim 1 of
  [[lem-power-monotone]] and covers $m = 0$ as well, since $a^{0} = 1 > 0$; and for
  $m < 0$ the value is $\big(a^{1/n}\big)^{m} = \Big(\big(a^{1/n}\big)^{-m}\Big)^{-1}$
  ([[lem-power-laws]], claim 2), the inverse of a positive element, hence positive
  ([[lem-of-inverse-positive]]). Note that [[lem-power-monotone]] is stated for
  natural exponents only, so it does not by itself settle the negative case; that
  is what the inverse step is for. The exponent laws are
  [[lem-rational-power-laws]] and the order behaviour is
  [[lem-rational-power-monotone]].
- **The exponent is a rational, never a real.** Nothing on this page is a limit,
  a series or a continuous function, and $a^{r}$ is computed in finitely many
  field operations once the root is available. What would be needed to go
  further, why it is deferred here, and where the library later defines $a^{x}$
  for real $x$ are recorded in [[rem-real-exponents-deferred]].
- The convention $0^0 = 1$ of [[def-integer-power]] is untouched: $r = 0$ is not
  covered by the supplementary clause, which asks for $r > 0$. So $0^0 = 1$ while
  $0^{r} = 0$ for every rational $r > 0$. There is no inconsistency, only the
  familiar fact that the two-variable function $(a, r) \mapsto a^{r}$ has no
  continuous extension to $(0,0)$, a statement this library cannot even make yet.
````

### `def-real-limit`

````markdown
---
id: def-real-limit
kind: definition
title: "Limits and Cauchy sequences of reals"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [def-real-numbers, def-real-order]
aliases: []
verification:
  precheck: n/a
  audited: 2026-07-24
sources:
  scraped: []
  references:
    - title: "T. Tao, Analysis I, 3rd ed., §6.1"
      url: "https://terrytao.wordpress.com/books/analysis-i/"
    - title: "Cauchy sequence (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Cauchy_sequence"
pipeline_run: null
---

## Definition

A sequence $(x_k)$ of reals **converges** to $x \in \mathbb{R}$ when for
every rational $\varepsilon > 0$ there is $K$ with
$|x_k - x| < \hat\varepsilon$ for all $k \ge K$. It is **Cauchy** when for
every rational $\varepsilon > 0$ there is $K$ with
$|x_k - x_l| < \hat\varepsilon$ for all $k, l \ge K$.

## Remarks

- Quantifying over rational $\varepsilon$ loses nothing: below any real
  $\varepsilon > 0$ lies a positive rational ([[lem-rat-embeds-dense]]).
- $|\cdot|$ is the absolute value of [[def-real-order]].
````

### `def-series`

````markdown
---
id: def-series
kind: definition
title: "Series, partial sums, convergence and the sum, divergence, and the tail series"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [def-finite-sum, def-sequence, def-real-limit, def-real-numbers, lem-limit-unique]
justified_by: []
aliases: []
landmark: true
verification:
  precheck: n/a
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-27
  audited: 2026-07-27
sources:
  scraped: []
  references:
    - title: "Series (mathematics) (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Series_(mathematics)"
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 3"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "T. Tao, Analysis I, 3rd ed., §7.2"
      url: "https://terrytao.wordpress.com/books/analysis-i/"
    - title: "John K. Hunter, An Introduction to Real Analysis"
      url: "https://www.math.ucdavis.edu/~hunter/intro_analysis_pdf/intro_analysis.pdf"
pipeline_run: null
---

## Definition

Throughout, $\mathbb{R}$ is the complete ordered field ([[def-real-numbers]]) and
a **sequence of reals** is a function $a : \mathbb{N} \to \mathbb{R}$
([[def-sequence]]), written $(a_k)$; recall that $\mathbb{N}$ contains $0$.

**Partial sums.** Let $(a_k)$ be a sequence of reals. Its **sequence of partial
sums** is

$$s_n \;:=\; \sum_{k < n} a_k \qquad (n \in \mathbb{N}),$$

the finite sum of [[def-finite-sum]]. In particular $s_0 = 0$, the empty sum, and
$s_{n+1} = s_n + a_n$ for every $n$, those being exactly the two recursion clauses
that define the finite sum. Note that $s_n$ is the sum of the $n$ terms
$a_0, \dots, a_{n-1}$, so the index $n$ counts terms rather than naming the last
one.

**Convergence, the sum, divergence.** The **series** of $(a_k)$, written
$\sum a_k$, **converges** when the sequence $(s_n)$ of partial sums converges
([[def-real-limit]]), and then the **sum of the series** is

$$\sum_{k=0}^{\infty} a_k \;:=\; \lim_{n} s_n .$$

The series **diverges** when $(s_n)$ does not converge. A convergent sequence of
reals has exactly one limit ([[lem-limit-unique]]), so the displayed symbol names
a single real number and nothing further has to be checked for it to be
well defined.

**Series with a general starting index.** Let $m \in \mathbb{N}$ and let $a$ be a
function on $\{\, k \in \mathbb{N} : k \ge m \,\}$, which we call a **family from
$m$** and write $(a_k)_{k \ge m}$. The series

$$\sum_{k \ge m} a_k$$

is by definition the series of the sequence $b_j := a_{j + m}$,
$j \in \mathbb{N}$, which is a genuine sequence of reals; it converges exactly
when that series converges, and its sum is then written
$\sum_{k = m}^{\infty} a_k$. Its partial sums are

$$\sum_{k=m}^{n-1} a_k \;=\; \sum_{j < n-m} a_{m+j} \qquad (n \ge m),$$

in the notation of [[def-finite-sum]], the value at $n = m$ being the empty sum
$0$. A sequence on $\mathbb{N}$ is the case $m = 0$, and the two readings of
$\sum a_k$ agree there, since $b_j = a_j$.

**This clause is not a convenience.** Sequences in this library are functions on
$\mathbb{N}$ and $\mathbb{N}$ contains $0$ ([[def-sequence]]), while many of the
classical series are built from expressions that are undefined at the index $0$:
$1/k$, $1/k^{p}$ and $|a_k|^{1/k}$ all require $k \ge 1$. Writing such a series as
$\sum_{k \ge 1} a_k$ names an honest object, whereas writing it as a sequence on
$\mathbb{N}$ would require a value at an index where the defining expression has
none. Every statement on this page says which starting index it uses.

**Tail series.** For $N \in \mathbb{N}$, the **$N$-th tail series** of
$\sum a_k$ is $\sum_{k \ge N} a_k$, that is the series of the $N$-th tail
$a^{(N)}$ of [[def-sequence]], whose terms are $a^{(N)}_j = a_{j+N}$. The
$0$-th tail series is the series itself.

## Remarks

- **"Diverges" here means "does not converge", and nothing more.** A divergent
  series may have partial sums that run away to $+\infty$, or to $-\infty$, or
  that oscillate without settling anywhere. The three behaviours are not
  distinguished by the word, and no statement on this page uses "diverges" to
  mean "the partial sums are unbounded" unless it says so.

- **The symbol $\sum_{k=0}^{\infty} a_k$ is defined only for a convergent
  series.** It denotes a real number, not a formal object, and it is illegitimate
  to write it down before convergence has been established. Where a proof needs
  to speak of the series without knowing whether it converges, it speaks of
  $(a_k)$ and of $(s_n)$.

- **Two indices, doing different work.** The index $k$ runs over the terms and is
  bound; the index $n$ runs over the partial sums and is the variable in which the
  limit is taken. Confusing them is the commonest slip in the subject, and it is
  the reason the definition above fixes $s_n = \sum_{k<n} a_k$ rather than
  $\sum_{k \le n} a_k$: with this choice the recursion $s_{n+1} = s_n + a_n$ is
  the one supplied by [[def-finite-sum]], with no shift anywhere.
````

### `def-series-of-vectors-and-rearrangement`

````markdown
---
id: def-series-of-vectors-and-rearrangement
kind: definition
title: "Series of vectors in $\\mathbb{R}^n$, absolute convergence, rearrangement, and the set of rearrangement sums"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [def-euclidean-inner-product, def-p-norms-on-rn, lem-p-norms-are-norms-and-induce-the-published-metrics, thm-componentwise-convergence-and-completeness, thm-all-norms-on-rn-are-equivalent, def-equivalent-norms, def-metric-convergence, def-series, def-absolute-and-conditional-convergence, def-rearrangement-and-unconditional-convergence, lem-standard-basis-of-f-n, def-linear-combination-and-span, def-finite-sum, lem-finite-sum-laws, def-sequence, def-injection-surjection-bijection, def-vector-space, lem-metrics-on-rn, lem-metric-limits-unique, def-isometry-and-metric-embedding, def-norm-and-normed-space]
justified_by: []
aliases: []
landmark: false
verification:
  precheck: n/a
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-28
  audited: 2026-07-29
sources:
  scraped: []
  references:
    - title: "Series (mathematics) (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Series_(mathematics)"
    - title: "Absolute convergence (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Absolute_convergence"
    - title: "T. Banakh, A Simple Inductive Proof of the Levy-Steinitz Theorem"
      url: "https://arxiv.org/abs/1711.04136"
pipeline_run: null
---

## Definition

Let $n \in \mathbb{N}$ with $n \ge 1$, so that $\mathbb{R}^{n}$ carries the
Euclidean metric $d_2$ ([[lem-metrics-on-rn]],
[[lem-p-norms-are-norms-and-induce-the-published-metrics]]). A **sequence of
vectors** is a function $x : \mathbb{N} \to \mathbb{R}^{n}$, written $(x_k)$ with
$x_k := x(k)$; as everywhere in this library $\mathbb{N}$ contains $0$ and a
sequence is indexed from $0$ ([[def-sequence]], [[def-metric-convergence]]).

### Partial sums and convergence

The **partial sums** of $(x_k)$ are

$$s_N \;:=\; \sum_{k<N} x_k \;\in\; \mathbb{R}^{n} \qquad (N \in \mathbb{N}),$$

the finite sum of the vector space $\mathbb{R}^{n}$
([[def-linear-combination-and-span]]), so $s_0 = 0$ and $s_{N+1} = s_N + x_N$.
**No third notion of finite sum is introduced**: by
[[lem-standard-basis-of-f-n]] clause 1 the vector sum is computed pointwise,
$(s_N)(j) = \sum_{k<N} x_k(j)$ for $j<n$, the right-hand side being the real
finite sum of [[def-finite-sum]].

The **series** $\sum x_k$ **converges to $s \in \mathbb{R}^{n}$** when
$s_N \to s$ in $(\mathbb{R}^{n}, d_2)$ ([[def-metric-convergence]]), and then $s$
is **the sum**, written $\sum_{k=0}^{\infty}x_k$. The symbol denotes a single
vector, because a sequence in a metric space has at most one limit
([[lem-metric-limits-unique]]). The series **diverges** when $(s_N)$ does not
converge.

### Absolute convergence

$\sum x_k$ **converges absolutely** when the real series
$\sum \lVert x_k\rVert_2$ converges ([[def-series]]); since
$\lVert x_k\rVert_2 \ge 0$ ([[def-norm-and-normed-space]]), this is a statement
about a series of nonnegative terms, exactly as in
[[def-absolute-and-conditional-convergence]].

**The choice of norm is immaterial.** If $N$ is any norm on $\mathbb{R}^{n}$ then
$c\lVert x_k\rVert_2 \le N(x_k) \le C\lVert x_k\rVert_2$ for fixed $c, C > 0$
([[thm-all-norms-on-rn-are-equivalent]], [[def-equivalent-norms]]), so
$\sum N(x_k)$ converges exactly when $\sum\lVert x_k\rVert_2$ does, both being
series of nonnegative terms. The notion defined above therefore depends on
$\mathbb{R}^{n}$ and not on the norm chosen to test it.

### Rearrangement and the set of rearrangement sums

Let $\sigma : \mathbb{N} \to \mathbb{N}$ be a bijection
([[def-injection-surjection-bijection]]). The **rearrangement of $\sum x_k$ along
$\sigma$** is the series $\sum x_{\sigma(k)}$ of the sequence
$k \mapsto x_{\sigma(k)}$, verbatim as in
[[def-rearrangement-and-unconditional-convergence]] one dimension down. The
**set of rearrangement sums** of $(x_k)$ is

$$\mathcal{S}(x) \;:=\; \Bigl\{\, s \in \mathbb{R}^{n} \;:\; \text{some rearrangement of } \sum x_k \text{ converges to } s \,\Bigr\}.$$

Taking $\sigma$ to be the identity shows that a convergent $\sum x_k$ has its own
sum in $\mathcal{S}(x)$, so $\mathcal{S}(x) \ne \varnothing$ for a convergent
series.

### Agreement with the one-dimensional theory

$\mathbb{R}^{1}$ is the set of functions $1 \to \mathbb{R}$ and is **not
literally** $\mathbb{R}$. The map $\theta : \mathbb{R} \to \mathbb{R}^{1}$ sending
$t$ to the function with value $t$ at $0$ is a bijection; it preserves addition
and scalar multiplication, since both are computed pointwise
([[def-vector-space]], [[lem-standard-basis-of-f-n]]), and
$d_2(\theta(s),\theta(t)) = |s-t|$, so it is an isometric bijection
([[def-isometry-and-metric-embedding]]). Under that identification, and for
$n = 1$:

- the partial sums above are the partial sums of [[def-series]];
- convergence and the sum are those of [[def-series]];
- absolute convergence is that of [[def-absolute-and-conditional-convergence]],
  since $\lVert\theta(t)\rVert_2 = |t|$;
- rearrangement is that of [[def-rearrangement-and-unconditional-convergence]];
- $\mathcal{S}(x)$ is the image under $\theta$ of the set of rearrangement sums
  that the published remark [[rem-rearrangement-in-higher-dimensions]] writes
  $\mathcal{S}(a)$.

**Every comparison on this page between $\mathbb{R}^{n}$ and the published
one-dimensional theory goes through this identification, and it is stated each
time.**

## Remarks

- **Where $n \ge 1$ comes from.** Convergence is tested with $d_2$, and
  [[lem-metrics-on-rn]] defines the metrics on $\mathbb{R}^{n}$ only for
  $n \ge 1$. The algebra above — partial sums, rearrangement, the set
  $\mathcal{S}(x)$ as a set of vectors — makes sense at $n = 0$ as well, but
  nothing on this page is asserted there.

- **Convergence is componentwise.** By
  [[thm-componentwise-convergence-and-completeness]] clause 1 and the pointwise
  formula for partial sums, $\sum x_k$ converges to $s$ if and only if the $n$
  real series $\sum (x_k)_j$ converge, with sums $s_j$. That is the form every
  proof below uses, and it is what reduces the vector theory to the published
  scalar theory rather than duplicating it.

- **Unconditional convergence is not defined here.** The one-dimensional notion is
  [[def-rearrangement-and-unconditional-convergence]], and over $\mathbb{R}$ it
  coincides with absolute convergence ([[cor-unconditional-iff-absolute-in-r]]).
  Whether that coincidence survives to $\mathbb{R}^{n}$ for $n \ge 2$ is not
  settled anywhere on this page, and nothing here asserts it in either direction.
  What **is** proved is that absolute convergence implies convergence of every
  rearrangement to the same sum ([[thm-absolute-convergence-in-rn]]).
````

### `def-the-space-of-summing-directions`

````markdown
---
id: def-the-space-of-summing-directions
kind: definition
title: "The subspace $\\Gamma$ of directions along which a series converges absolutely, and its orthogonal complement $\\Gamma^{\\perp}$"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: not-applicable
deps: [def-series-of-vectors-and-rearrangement, def-euclidean-inner-product, thm-cauchy-schwarz-and-the-euclidean-norm, thm-absolute-convergence-in-rn, lem-every-norm-on-rn-is-continuous-for-the-euclidean-metric, def-p-norms-on-rn, def-linear-subspace, lem-linear-subspace-criterion, lem-intersection-of-linear-subspaces, def-vector-space, def-series, lem-series-linearity, thm-direct-comparison-test, lem-standard-basis-of-f-n, def-absolute-and-conditional-convergence, lem-of-abs-value, lem-finite-sum-laws, def-finite-sum, thm-induction-principle, def-norm-and-normed-space]
justified_by: []
aliases: []
landmark: false
verification:
  precheck: n/a
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-28
  audited: 2026-07-29
sources:
  scraped: []
  references:
    - title: "Levy-Steinitz theorem (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/L%C3%A9vy%E2%80%93Steinitz_theorem"
    - title: "Linear subspace (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Linear_subspace"
    - title: "T. Banakh, A Simple Inductive Proof of the Levy-Steinitz Theorem"
      url: "https://arxiv.org/abs/1711.04136"
pipeline_run: null
---

## Definition

Let $n \in \mathbb{N}$ with $n \ge 1$ and let $(x_k)$ be a sequence in
$\mathbb{R}^{n}$ ([[def-series-of-vectors-and-rearrangement]]). Define

$$\Gamma \;:=\; \Bigl\{\, a \in \mathbb{R}^{n} \;:\; \sum_k \bigl|\langle a, x_k\rangle\bigr| \text{ converges} \,\Bigr\}, \qquad \Gamma^{\perp} \;:=\; \bigl\{\, y \in \mathbb{R}^{n} \;:\; \langle a, y\rangle = 0 \text{ for every } a \in \Gamma \,\bigr\},$$

the inner product being the Euclidean one ([[def-euclidean-inner-product]]) and
the series that of [[def-series]]. Elements of $\Gamma$ are the **summing
directions** of $(x_k)$: those $a$ for which the real series of the projections
$\langle a, x_k\rangle$ converges absolutely
([[def-absolute-and-conditional-convergence]]). Both sets depend on the sequence
$(x_k)$; when several are in play the notation is $\Gamma(x)$ and
$\Gamma(x)^{\perp}$.

**Phrased with the inner product, deliberately.** The classical statement uses
linear functionals and the dual space. This library has no definition of a linear
map at this point in the reading order — the page that introduces linear maps,
rank-nullity and quotient spaces comes **earlier in the plan order** and is not
yet built — so writing $\Gamma$ with functionals would mint that page's canonical
object here. The two descriptions agree on $\mathbb{R}^{n}$, and nothing on this
page depends on their agreement.

### Both are linear subspaces

**$\Gamma$ is a linear subspace of $\mathbb{R}^{n}$** ([[def-linear-subspace]]).
It is nonempty: $\langle 0, x_k\rangle = 0$ for every $k$ by bilinearity, and the
series with all terms $0$ converges. For $\lambda \in \mathbb{R}$ and
$a, b \in \Gamma$, bilinearity and the absolute value laws give

$$\bigl|\langle \lambda a + b, x_k\rangle\bigr| \;=\; \bigl|\lambda\langle a,x_k\rangle + \langle b,x_k\rangle\bigr| \;\le\; |\lambda|\,\bigl|\langle a,x_k\rangle\bigr| + \bigl|\langle b,x_k\rangle\bigr|$$

([[lem-of-abs-value]]), and the series of the right-hand side converges by
[[lem-series-linearity]] clauses 1 and 2, so the left-hand series converges by
the comparison test ([[thm-direct-comparison-test]], the terms being
nonnegative). By the one-step subspace test
([[lem-linear-subspace-criterion]]), $\Gamma$ is a linear subspace.

**$\Gamma^{\perp}$ is a linear subspace of $\mathbb{R}^{n}$.** It contains $0$,
and for $\lambda \in \mathbb{R}$, $y, z \in \Gamma^{\perp}$ and $a \in \Gamma$,
bilinearity gives $\langle a, \lambda y + z\rangle = \lambda\langle a,y\rangle + \langle a,z\rangle = 0$;
again [[lem-linear-subspace-criterion]] applies. Equivalently $\Gamma^{\perp}$ is
the intersection of the linear subspaces
$\{y : \langle a,y\rangle = 0\}$ over $a \in \Gamma$, a nonempty family since
$0 \in \Gamma$, and [[lem-intersection-of-linear-subspaces]] gives the same
conclusion.

### $\Gamma$ is everything exactly when the series converges absolutely

**If $\sum x_k$ converges absolutely then $\Gamma = \mathbb{R}^{n}$.** For any
$a$, Cauchy-Schwarz gives
$|\langle a,x_k\rangle| \le \lVert a\rVert_2\lVert x_k\rVert_2$
([[thm-cauchy-schwarz-and-the-euclidean-norm]]), and
$\sum_k \lVert a\rVert_2\lVert x_k\rVert_2$ converges by
[[lem-series-linearity]] clause 2; the comparison test gives $a \in \Gamma$.

**Conversely, if $\Gamma = \mathbb{R}^{n}$ then $\sum x_k$ converges
absolutely.** Each standard basis vector $e_j$ lies in $\Gamma$, and
$\langle e_j, x_k\rangle = (x_k)_j$ ([[lem-standard-basis-of-f-n]],
[[def-euclidean-inner-product]]), so each real series $\sum_k |(x_k)_j|$
converges. A finite sum of convergent series converges, by
[[lem-series-linearity]] clause 1 and induction on the number of summands
([[thm-induction-principle]], [[lem-finite-sum-laws]], [[def-finite-sum]]), so
$\sum_k \sum_{j<n}|(x_k)_j| = \sum_k \lVert x_k\rVert_1$ converges; and
$\lVert x_k\rVert_2 \le \lVert x_k\rVert_1$
([[lem-every-norm-on-rn-is-continuous-for-the-euclidean-metric]] clause 3,
[[def-p-norms-on-rn]]), so $\sum_k\lVert x_k\rVert_2$ converges by the comparison
test.

**That equivalence is what makes the containment theorem below contain
[[thm-absolute-convergence-in-rn]] as a special case**: absolute convergence
gives $\Gamma = \mathbb{R}^{n}$, hence $\Gamma^{\perp} = \{0\}$ (any
$y \in \Gamma^{\perp}$ satisfies $\langle y,y\rangle = 0$ and so $y = 0$ by
positive definiteness), and the affine subspace below collapses to a point.

### Affine subspaces

The library has no notion of an affine subspace, so one is fixed here. For a
linear subspace $W \subseteq \mathbb{R}^{n}$ and $s \in \mathbb{R}^{n}$, the
**affine subspace through $s$ with direction $W$** is the coset

$$s + W \;:=\; \{\, s + w \;:\; w \in W \,\} .$$

**A coset is determined by $W$ together with any one of its points.** If
$p \in s + W$, say $p = s + w_0$ with $w_0 \in W$, then $p + W = s + W$: every
$p + w = s + (w_0 + w)$ lies in $s+W$ because $W$ is closed under addition, and
every $s + w = p + (w - w_0)$ lies in $p + W$ because $W$ is closed under
addition and under multiplication by $-1$ ([[def-linear-subspace]],
[[def-vector-space]]). In particular $s + W = s' + W$ if and only if
$s - s' \in W$.

## Remarks

- **$0 \in \Gamma$ always, so $\Gamma$ is never empty and $\Gamma^{\perp}$ is
  never larger than $\mathbb{R}^{n}$ by accident.** At the other extreme, if
  $\Gamma = \{0\}$ then $\Gamma^{\perp} = \mathbb{R}^{n}$, the condition on $y$
  being vacuous apart from $a = 0$.

- **The definition does not presuppose convergence of $\sum x_k$**, and neither
  $\Gamma$ nor $\Gamma^{\perp}$ mentions the sum. Convergence is a hypothesis of
  the theorems that use them, not of the definition.

- **No orthogonal decomposition is claimed.** Nothing here asserts that
  $\mathbb{R}^{n}$ is the direct sum of $\Gamma$ and $\Gamma^{\perp}$, or that
  $(\Gamma^{\perp})^{\perp} = \Gamma$. Those are statements of the theory of
  inner product spaces and orthogonality, which is planned for a page earlier in
  the plan order that is not yet built, and **no item on this page uses them**.
  What is used is only that $\Gamma^{\perp}$ is a linear subspace and that
  $\langle a, y\rangle = 0$ for $a \in \Gamma$, $y \in \Gamma^{\perp}$.

- **The name.** $\Gamma$ is the set of directions in which the series is
  absolutely summable; along a direction outside $\Gamma$ the projected real
  series converges conditionally at best, and it is exactly there that
  rearrangement can move the sum.
````

### `lem-alternating-sequence`

````markdown
---
id: lem-alternating-sequence
kind: lemma
title: "The even and odd index maps and the alternating sequence: strictly increasing $e, o$ with $\\mathbb{N}$ their disjoint union, and the unique $(s_k)$ with $s_0 = 1$, $s_{\\sigma(k)} = -s_k$, which satisfies $|s_k| = 1$, $s \\circ e \\equiv 1$ and $s \\circ o \\equiv -1$"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-generated
deps: [thm-recursion, thm-induction-principle, lem-index-map-grows, def-sequence, def-natural-numbers, def-nat-addition, def-nat-order, thm-nat-linear-order, lem-nat-successor-neq-self, def-abs-value, lem-of-abs-value, def-real-order, cor-of-one-positive, lem-of-add-order, def-complete-ordered-field, def-ordered-field, def-field]
justified_by: []
forward_refs: [ex-two-subsequential-limits, cex-unbounded-with-convergent-subsequence]
aliases: []
landmark: false
proof_strategy: induction
verification:
  precheck: pass
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-26
  audited: 2026-07-26
sources:
  scraped: []
  references:
    - title: "Parity (mathematics) (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Parity_(mathematics)"
    - title: "Subsequence (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Subsequence"
    - title: "T. Tao, Analysis I, 3rd ed., §2.1 and §6.4 (recursive definitions; subsequences)"
      url: "https://terrytao.wordpress.com/books/analysis-i/"
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 3"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
---

## Statement

Let $\sigma$ be the successor on $\mathbb{N}$ ([[def-natural-numbers]]). There are
functions $e, o : \mathbb{N} \to \mathbb{N}$ and a sequence $(s_k)$ of reals
([[def-sequence]]) with the following properties.

1. **The index maps.** $e$ is the unique function with
   $e_0 = 0$ and $e_{\sigma(j)} = \sigma(\sigma(e_j))$, and $o$ the unique
   function with $o_0 = \sigma(0)$ and $o_{\sigma(j)} = \sigma(\sigma(o_j))$.
   Both are **strictly increasing**.
2. **The partition.** $\mathbb{N}$ is the **disjoint union** of the ranges of $e$
   and of $o$: every natural number is $e_i$ for exactly one $i$ or $o_i$ for
   exactly one $i$, and never both.
3. **The alternating sequence.** $(s_k)$ is the **unique** sequence of reals with
   $$s_0 = 1, \qquad s_{\sigma(k)} = -s_k \quad (k \in \mathbb{N}).$$
4. **Its values.** $|s_k| = 1$ for every $k$, so $(s_k)$ is bounded; and
   $$s_{e_j} = 1, \qquad s_{o_j} = -1 \qquad (j \in \mathbb{N}),$$
   that is $s \circ e$ is constantly $1$ and $s \circ o$ constantly $-1$.

This is the sequence usually written $s_k = (-1)^k$, with $e_j = 2j$ and
$o_j = 2j+1$, presented by the recursions that its proofs actually use. It is
collected here once because three separate items on this page and its companion
need an alternating or interleaved witness, and rebuilding the recursion inside
each of them is what this lemma exists to prevent.

## Facts & Assumptions

**Given:** By the recursion theorem ([[thm-recursion]]) applied to the set $\mathbb{R}$, the element $1$ and the function $u \mapsto -u$, the unique sequence $(s_k)$ of reals with $s_0 = 1$ and $s_{\sigma(k)} = -s_k$; applied to the set $\mathbb{N}$, the element $0$ and the function $i \mapsto \sigma(\sigma(i))$, the unique $e : \mathbb{N} \to \mathbb{N}$ with $e_0 = 0$ and $e_{\sigma(j)} = \sigma(\sigma(e_j))$; and applied to $\mathbb{N}$, the element $\sigma(0)$ and the same function, the unique $o : \mathbb{N} \to \mathbb{N}$ with $o_0 = \sigma(0)$ and $o_{\sigma(j)} = \sigma(\sigma(o_j))$ ([[def-natural-numbers]], [[def-sequence]]).

[L1] Recursion theorem, including its uniqueness clause ([[thm-recursion]]).

[L2] Induction principle ([[thm-induction-principle]]).

[L3] Order on $\mathbb{N}$: $i < \sigma(i)$ for every $i$, since $\sigma(i) = i + 1$ gives $i \le \sigma(i)$ and $\sigma(i) \ne i$; and the order is transitive and total ([[def-nat-order]], [[def-nat-addition]], [[lem-nat-successor-neq-self]], [[thm-nat-linear-order]]).

[L4] Consecutive comparisons suffice: if $n_i < n_{\sigma(i)}$ for every $i$ then $n$ is strictly increasing ([[lem-index-map-grows]]).

[L5] Absolute value and field arithmetic: $|-u| = |u|$ ([[lem-of-abs-value]]); $|v| = v$ whenever $v \ge 0$ ([[def-abs-value]], [[def-real-order]]); and $-(-u) = u$ ([[def-field]]).

[L6] Order in $\mathbb{R}$: $0 < 1$ ([[cor-of-one-positive]]), sums of positives are positive and adding a constant preserves the order ([[lem-of-add-order]], [[def-complete-ordered-field]], [[def-ordered-field]]), so $1 - (-1) = 1 + 1 > 0$ and hence $-1 < 1$; in particular $1 \ne -1$.

## Proof

**Proof technique:** induction.

1.1 Base case for claim 4: $|s_0| = |1| = 1$, since $1 > 0$ makes $|1| = 1$. [given, L5, L6, base]

1.2 Inductive hypothesis: fix $k \in \mathbb{N}$ and assume $|s_k| = 1$. [ih]

1.3 Both index maps satisfy consecutive strict comparisons: $e_j < \sigma(e_j) < \sigma(\sigma(e_j)) = e_{\sigma(j)}$, and likewise $o_j < o_{\sigma(j)}$, so $e$ and $o$ are strictly increasing and claim 1 holds, its uniqueness part being the uniqueness clause of the recursion theorem. [given, L1, L3, L4]

1.4 By induction, $s_{e_j} = 1$ for every $j$: the base case is $s_{e_0} = s_0 = 1$, and if $s_{e_j} = 1$ then $s_{e_{\sigma(j)}} = s_{\sigma(\sigma(e_j))} = -s_{\sigma(e_j)} = -(-s_{e_j}) = s_{e_j} = 1$. [given, L1, L2, L5]

1.5 By induction, $s_{o_j} = -1$ for every $j$: the base case is $s_{o_0} = s_{\sigma(0)} = -s_0 = -1$, and if $s_{o_j} = -1$ then $s_{o_{\sigma(j)}} = s_{\sigma(\sigma(o_j))} = -(-s_{o_j}) = s_{o_j} = -1$. [given, L1, L2, L5]

1.6 By induction on $n$, every natural number satisfies: either $n = e_i$ and $\sigma(n) = o_i$ for some $i$, or $n = o_i$ and $\sigma(n) = e_{\sigma(i)}$ for some $i$. The base case is $0 = e_0$ with $\sigma(0) = o_0$. For the successor step, if $n = e_i$ and $\sigma(n) = o_i$ then $\sigma(n) = o_i$ and $\sigma(\sigma(n)) = \sigma(\sigma(e_i)) = e_{\sigma(i)}$, which is the second alternative at $\sigma(n)$; and if $n = o_i$ and $\sigma(n) = e_{\sigma(i)}$ then $\sigma(n) = e_{\sigma(i)}$ and $\sigma(\sigma(n)) = \sigma(\sigma(o_i)) = o_{\sigma(i)}$, which is the first alternative at $\sigma(n)$. [given, L1, L2]

1.7 The sequence $(s_k)$ is the unique sequence of reals with $s_0 = 1$ and $s_{\sigma(k)} = -s_k$, by the uniqueness clause of the recursion theorem: this is claim 3. [given, L1]

2.1 Successor step for claim 4: $|s_{\sigma(k)}| = |-s_k| = |s_k| = 1$. [step 1.2, L5]

2.2 In particular every natural number lies in the range of $e$ or in the range of $o$, since each alternative of step 1.6 exhibits $n$ as such a value. [step 1.6]

2.3 The two ranges are disjoint: if $e_i = o_j$ for some $i, j$ then $1 = s_{e_i} = s_{o_j} = -1$, contradicting $1 \ne -1$. [step 1.4, step 1.5, L6]

2.4 Each of $e$ and $o$ is injective, being strictly increasing, so a natural number in the range of $e$ is $e_i$ for exactly one $i$, and likewise for $o$. [step 1.3, L3]

3.1 By the induction principle, $|s_k| = 1$ for every $k \in \mathbb{N}$; hence $|s_k| \le 1$ at every index and $(s_k)$ is bounded. Together with steps 1.4 and 1.5 this is claim 4. [step 1.1, step 2.1, step 1.4, step 1.5, L2]

4.1 Claim 2 follows: by step 2.2 every natural is in one of the two ranges, by step 2.3 not in both, and by step 2.4 the index realising it is unique. Claims 1, 2, 3 and 4 are therefore all established. [step 2.2, step 2.3, step 3.1, step 2.4, step 1.3, step 1.7, discharge-induction] ∎

## Remarks

- **Why the recursion rather than $(-1)^k$.** Written as a power, every one of the
  four claims would have to be unwound into the two recursion equations before it
  could be proved; written as a recursion, each is a two-line induction. The
  identification with $(-1)^k$ is available ([[def-integer-power]]) and is used
  nowhere.

- **The parity statement is genuinely proved, not assumed.** Claim 2 is where the
  work is: the covering half is the interleaved induction of step 1.6, which
  tracks $n$ and $\sigma(n)$ together because neither alone is preserved by the
  successor, and the disjointness half is settled by the *sequence*, since
  $s$ takes the value $1$ on one range and $-1$ on the other and $1 \ne -1$.
  Using the sequence to separate the two ranges is shorter than any direct parity
  argument and needs no arithmetic on $\mathbb{N}$ beyond the successor.

- **What consumes this lemma.** [[fs-convergent-subsequence-implies-bounded]]
  interleaves a constant sequence with an unbounded one along $e$ and $o$;
  [[ex-two-subsequential-limits]] multiplies $s$ by a null perturbation to get a
  sequence with exactly two subsequential limits; and
  [[cex-unbounded-with-convergent-subsequence]] is the witness for the first of
  those. The same sequence, built inline, refutes
  [[fs-bounded-implies-convergent]] on the previous page; that item predates this
  lemma and is left as it stands.
````

### `lem-of-abs-value`

````markdown
---
id: lem-of-abs-value
kind: lemma
title: "Basic properties of the absolute value"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-altered
deps: [def-abs-value, def-ordered-field, lem-of-mult-neg, lem-of-sign-rules]
aliases: []
landmark: false
short: "|x| properties"
proof_strategy: cases
verification:
  precheck: pass
  judge:
    model: openai/gpt-5.4
    verdict: pass
    date: 2026-07-25
  audited: 2026-07-25
sources:
  scraped: []
  references:
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 1"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "T. Tao, Analysis I, 3rd ed."
      url: "https://terrytao.wordpress.com/books/analysis-i/"
    - title: "Purdue University analysis notes: Ordered fields and absolute value"
      url: "https://www.math.purdue.edu/~gcavigli/Swanson.pdf"
pipeline_run: null
---

## Statement

Let $F$ be an ordered field ([[def-ordered-field]]) and let $x, y \in F$, with
$|x|$ the absolute value ([[def-abs-value]]). Then

$$|x| \ge 0; \quad |x| = 0 \iff x = 0; \quad -|x| \le x \le |x|; \quad |-x| = |x|; \quad |xy| = |x|\,|y|;$$

and, for every $c > 0$, one has $|x| < c \iff -c < x < c$.

## Facts & Assumptions

**Given:** An ordered field $F$ and elements $x, y \in F$.

[L1] Absolute value: $|u| = u$ if $u \ge 0$, and $|u| = -u$ if $u < 0$ ([[def-abs-value]]).

[L2] Ordered-field order: trichotomy holds (for each $u$ exactly one of $u > 0$, $u = 0$, $u < 0$), $a < b$ means $b - a$ is positive, and sums and products of positives are positive ([[def-ordered-field]]).

[L3] Signs in products: $(-a)b = -(ab)$ and $(-a)(-b) = ab$ ([[lem-of-mult-neg]]).

[L4] Sign rules: a product of two elements of the same sign is positive, and a product of two elements of opposite sign is negative ([[lem-of-sign-rules]]).

## Proof

**Proof technique:** cases.

1.1 Case $x > 0$: by [L1] $|x| = x > 0$, so $|x| \ge 0$ and $|x| \ne 0$; since $-x < 0$ we get $|-x| = -(-x) = x = |x|$ by [L1], and $-|x| = -x < 0 < x = |x|$, so $-|x| \le x \le |x|$. [assume-case pos, L1, L2, algebra]

1.2 Case $x = 0$: then $|x| = |0| = 0$, so $|x| \ge 0$ holds with $|x| = 0$ and $x = 0$, while $|-x| = |0| = |x|$ and $-|x| = 0 \le 0 \le 0 = |x|$. [assume-case zero, L1]

1.3 Case $x < 0$: by [L1] $|x| = -x$, and [L2] gives $-x > 0$, so $|x| > 0$ and $|x| \ne 0$; here $|-x| = -x = |x|$ by [L1], and $-|x| = -(-x) = x \le x$ while $x < 0 < -x = |x|$, so $-|x| \le x \le |x|$. [assume-case neg, L1, L2, algebra]

1.4 Case $x = 0$ or $y = 0$: then $xy = 0$, so $|xy| = 0$, and one of $|x|, |y|$ is $0$, whence $|x|\,|y| = 0 = |xy|$. [assume-case zerofactor, L1]

1.5 Case $x, y$ have the same sign (both positive or both negative): by [L4] $xy > 0$, so $|xy| = xy$, while $|x|\,|y| = xy$ by [L3] (for $x, y < 0$ this is $(-x)(-y) = xy$), hence $|xy| = |x|\,|y|$. [assume-case same, L1, L3, L4]

1.6 Case $x, y$ have opposite signs (one positive, one negative): by [L4] $xy < 0$, so $|xy| = -(xy)$, while $|x|\,|y| = -(xy)$ by [L3] (namely $x(-y)$ or $(-x)y$), hence $|xy| = |x|\,|y|$. [assume-case opposite, L1, L3, L4]

2.1 By trichotomy [L2] each $x$ lies in exactly one of the cases 1.1-1.3, and in each we verified $|x| \ge 0$, that $|x| = 0 \iff x = 0$, that $|-x| = |x|$, and that $-|x| \le x \le |x|$; hence all four hold for every $x$. [step 1.1, step 1.2, step 1.3, cases-exhaustive]

2.2 By trichotomy [L2] each pair $x, y$ lies in exactly one of the cases 1.4-1.6, and in each $|xy| = |x|\,|y|$; hence $|xy| = |x|\,|y|$ for all $x, y$. [step 1.4, step 1.5, step 1.6, cases-exhaustive]

3.1 Let $c > 0$: if $|x| < c$ then $-c < -|x| \le x \le |x| < c$ by [step 2.1] and [L2], so $-c < x < c$; conversely if $-c < x < c$ then both $x < c$ and $-x < c$, and since $|x|$ equals $x$ or $-x$ by [L1], we get $|x| < c$, so $|x| < c \iff -c < x < c$. [step 2.1, L1, L2] ∎
````

### `lem-of-inverse-positive`

````markdown
---
id: lem-of-inverse-positive
kind: lemma
title: "Inverses of positives are positive, and reciprocation reverses order"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-altered
deps: [def-ordered-field, lem-of-sign-rules, cor-of-one-positive]
aliases: []
landmark: false
verification:
  precheck: pass
  judge:
    model: openai/gpt-5.4
    verdict: pass
    date: 2026-07-25
  audited: 2026-07-25
sources:
  scraped: []
  references:
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 1"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "M. Spivak, Calculus, 4th ed., Ch. 1"
      url: "https://en.wikipedia.org/wiki/Michael_Spivak"
    - title: "University of Innsbruck notes: Ordered fields"
      url: "https://www.uibk.ac.at/media/filer_public/28/02/280225fd-dde6-4e9c-bff6-baad33ff4a05/ragen.pdf"
pipeline_run: null
proof_strategy: direct
---

## Statement

Let $F$ be an ordered field ([[def-ordered-field]]) with positive cone $P$, and
let $a, b \in F$.

1. If $a > 0$ then $a^{-1} > 0$.
2. If $0 < a < b$ then $0 < b^{-1} < a^{-1}$.

## Facts & Assumptions

**Given:** An ordered field $F$ with positive cone $P$, and elements $a, b \in F$.

[L1] $x > 0 \iff x \in P$; $x < 0 \iff -x \in P$; and for $x \neq 0$ exactly one of $x \in P$, $-x \in P$ holds ([[def-ordered-field]]).

[L2] Sign rules: a product of a positive and a negative is negative, a product of two positives is positive, and for $c > 0$ one has $a < b \iff ac < bc$ ([[lem-of-sign-rules]]).

[L3] $0 < 1$; in particular $1 \neq 0$ ([[cor-of-one-positive]]).

[L4] $P$ is closed under addition, so $<$ is transitive ([[def-ordered-field]]).

## Proof

**Proof technique:** direct.

1.1 Assume $a > 0$, so $a \neq 0$ and its inverse $a^{-1}$ exists with $a \cdot a^{-1} = 1$; moreover $a^{-1} \neq 0$, since $a^{-1}$ has $a$ as its inverse while $0$ is non-invertible ($1 \neq 0$ by L3). [assume-hyp, L1, L3]

2.1 By trichotomy $a^{-1} \in P$ or $-a^{-1} \in P$; if $-a^{-1} \in P$, then $a > 0$ and $a^{-1} < 0$ give $a \cdot a^{-1} < 0$ by the sign rules, i.e. $1 < 0$, contradicting $0 < 1$; hence $a^{-1} \in P$, i.e. $a^{-1} > 0$, proving claim 1. [step 1.1, L2, L3, L1]

3.1 Assume $0 < a < b$; then $0 < b$ by transitivity, so by claim 1 both $a^{-1} > 0$ and $b^{-1} > 0$, and the sign rules give $a^{-1} b^{-1} > 0$. [assume-hyp, step 2.1, L4, L2, L1]

4.1 Multiplying $a < b$ by the positive $a^{-1} b^{-1}$ via the sign rules gives $a (a^{-1} b^{-1}) < b (a^{-1} b^{-1})$; since $a a^{-1} = 1$ and $b b^{-1} = 1$, this simplifies to $b^{-1} < a^{-1}$. [step 3.1, L2, algebra]

5.1 Together with $b^{-1} > 0$ from step 3.1, we conclude $0 < b^{-1} < a^{-1}$, proving claim 2. [step 3.1, step 4.1] ∎
````

### `lem-of-naturals-positive`

````markdown
---
id: lem-of-naturals-positive
kind: lemma
title: "Canonical naturals are positive and strictly increasing"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-generated
deps: [cor-of-one-positive, lem-of-add-order, def-field]
aliases: []
landmark: false
short: "n·1 > 0"
proof_strategy: induction
verification:
  precheck: pass
  judge:
    model: openai/gpt-5.4
    verdict: pass
    date: 2026-07-25
  audited: 2026-07-25
sources:
  scraped: []
  references:
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 1"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "M. Spivak, Calculus, 4th ed., Ch. 1"
      url: "https://en.wikipedia.org/wiki/Michael_Spivak"
    - title: "Elias Zakon, Mathematical Analysis: Natural Numbers and Induction"
      url: "https://math.libretexts.org/Bookshelves/Analysis/Mathematical_Analysis_%28Zakon%29/02%3A_Real_Numbers_and_Fields/2.02%3A_Natural_Numbers._Induction"
pipeline_run: null
---

## Statement

Let $F$ be an ordered field, with field structure as in [[def-field]], and for
$n \ge 1$ let $n \cdot 1_F$ denote the canonical natural number
$\underbrace{1_F + \cdots + 1_F}_{n}$, defined recursively by $1 \cdot 1_F = 1_F$
and $(n+1) \cdot 1_F = n \cdot 1_F + 1_F$. Then for every $n \ge 1$:

- $n \cdot 1_F > 0$ and $(n+1) \cdot 1_F > n \cdot 1_F$;
- the map $n \mapsto n \cdot 1_F$ is strictly increasing, hence injective, on $\{1, 2, 3, \dots\}$;
- $(m+n) \cdot 1_F = m \cdot 1_F + n \cdot 1_F$ and $(mn) \cdot 1_F = (m \cdot 1_F)(n \cdot 1_F)$ for all $m, n \ge 1$.

## Facts & Assumptions

**Given:** An ordered field $F$ whose canonical naturals are defined recursively by $1 \cdot 1_F = 1_F$ and $(n+1) \cdot 1_F = n \cdot 1_F + 1_F$, with $0 \cdot 1_F = 0$.

[L1] $0 < 1_F$ in every ordered field ([[cor-of-one-positive]]).

[L2] The order is compatible with addition and positives are closed under addition: $a < b$ implies $a + c < b + c$, and $a > 0$, $b > 0$ imply $a + b > 0$ ([[lem-of-add-order]]).

## Proof

**Proof technique:** induction.

1.1 Base case $n = 1$: by definition $1 \cdot 1_F = 1_F$, and $1_F > 0$. [L1, base]

1.2 Inductive hypothesis: assume $n \cdot 1_F > 0$ for some fixed $n \ge 1$. [ih]

1.3 By the recursion, $(n+1) \cdot 1_F - n \cdot 1_F = 1_F > 0$, so $(n+1) \cdot 1_F > n \cdot 1_F$. [given, L1]

1.4 Additive identity: fix $m$ and induct on $n$; at $n = 1$, $(m+1) \cdot 1_F = m \cdot 1_F + 1_F$ by the recursion, and if $(m+n) \cdot 1_F = m \cdot 1_F + n \cdot 1_F$ then $(m+n+1) \cdot 1_F = (m+n) \cdot 1_F + 1_F = m \cdot 1_F + n \cdot 1_F + 1_F = m \cdot 1_F + (n+1) \cdot 1_F$. [given, algebra]

2.1 Inductive step: $(n+1) \cdot 1_F = n \cdot 1_F + 1_F$ is a sum of two positives, by the hypothesis and $1_F > 0$, hence $(n+1) \cdot 1_F > 0$. [step 1.2, L1, L2]

2.2 Iterating 1.3, for $m < n$ one has $m \cdot 1_F < n \cdot 1_F$, so $n \mapsto n \cdot 1_F$ is strictly increasing and therefore injective on $\{1, 2, 3, \dots\}$. [step 1.3, L2]

2.3 Multiplicative identity: fix $m$ and induct on $n$; at $n = 1$, $(m \cdot 1) \cdot 1_F = m \cdot 1_F = (m \cdot 1_F)(1 \cdot 1_F)$, and the step $(m(n+1)) \cdot 1_F = (mn + m) \cdot 1_F = (mn) \cdot 1_F + m \cdot 1_F = (m \cdot 1_F)(n \cdot 1_F) + (m \cdot 1_F)(1_F) = (m \cdot 1_F)((n+1) \cdot 1_F)$ uses 1.4 and distributivity. [step 1.4, algebra]

3.1 By induction on 1.1, 1.2, 2.1, $n \cdot 1_F > 0$ for every $n \ge 1$; with the strict increase 2.2 and the identities 1.4, 2.3, every claim holds. [step 2.1, step 2.2, step 1.4, step 2.3, discharge-induction] ∎
````

### `lem-series-linearity`

````markdown
---
id: lem-series-linearity
kind: lemma
title: "Convergent series add and scale termwise"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-generated
deps: [def-series, thm-algebra-of-limits, lem-finite-sum-laws, def-finite-sum]
justified_by: []
aliases: []
landmark: false
proof_strategy: direct
verification:
  precheck: pass
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-27
  audited: 2026-07-27
sources:
  scraped: []
  references:
    - title: "Series (mathematics) (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Series_(mathematics)"
    - title: "T. Tao, Analysis I, 3rd ed., §7.2"
      url: "https://terrytao.wordpress.com/books/analysis-i/"
    - title: "John K. Hunter, An Introduction to Real Analysis"
      url: "https://www.math.ucdavis.edu/~hunter/intro_analysis_pdf/intro_analysis.pdf"
pipeline_run: null
---

## Statement

Let $(a_k)$ and $(b_k)$ be sequences of reals whose series converge
([[def-series]]), and let $c \in \mathbb{R}$. Then:

1. $\sum (a_k + b_k)$ converges, with
   $\displaystyle\sum_{k=0}^{\infty}(a_k + b_k) = \sum_{k=0}^{\infty} a_k + \sum_{k=0}^{\infty} b_k$;
2. $\sum c\,a_k$ converges, with
   $\displaystyle\sum_{k=0}^{\infty} c\,a_k = c \sum_{k=0}^{\infty} a_k$.

Moreover, for $c \ne 0$ and an arbitrary sequence $(a_k)$, whose series is not
assumed to converge:

3. $\sum c\,a_k$ converges **if and only if** $\sum a_k$ converges. Equivalently,
   $\sum a_k$ diverges if and only if $\sum c\,a_k$ diverges.

Claim 3 is the form used whenever a comparison is made against a constant
multiple of a known series.

## Facts & Assumptions

**Given:** Sequences $(a_k)$, $(b_k)$ of reals and $c \in \mathbb{R}$, with partial sums $s_n = \sum_{k<n} a_k$ and $t_n = \sum_{k<n} b_k$ ([[def-series]], [[def-finite-sum]]).

[L1] Additivity and scaling of finite sums: $\sum_{k<n}(a_k + b_k) = \sum_{k<n} a_k + \sum_{k<n} b_k$ and $\sum_{k<n} c\,a_k = c \sum_{k<n} a_k$ ([[lem-finite-sum-laws]]).

[L2] Algebra of limits: if $x_n \to x$ and $y_n \to y$ then $x_n + y_n \to x + y$ and $c\,x_n \to c\,x$ ([[thm-algebra-of-limits]]).

## Proof

**Proof technique:** direct.

1.1 The partial sums of $\sum (a_k + b_k)$ are $\sum_{k<n}(a_k + b_k) = s_n + t_n$, and those of $\sum c\,a_k$ are $\sum_{k<n} c\,a_k = c\,s_n$. [given, L1]

1.2 Assume $\sum a_k$ and $\sum b_k$ converge, say $s_n \to S$ and $t_n \to T$. [given]

2.1 Then $s_n + t_n \to S + T$, so $\sum(a_k + b_k)$ converges with sum $S + T$, which is claim 1. [step 1.2, step 1.1, L2]

2.2 Likewise $c\,s_n \to c\,S$, so $\sum c\,a_k$ converges with sum $c\,S$, which is claim 2. [step 1.2, step 1.1, L2]

3.1 For claim 3, let $c \ne 0$ and let $(a_k)$ be arbitrary. If $\sum a_k$ converges then $\sum c\,a_k$ converges by claim 2. [step 2.2]

3.2 Conversely, if $\sum c\,a_k$ converges then applying claim 2 to the sequence $(c\,a_k)$ and the scalar $1/c$, which exists since $c \ne 0$, shows that $\sum (1/c)(c\,a_k) = \sum a_k$ converges. [step 2.2, algebra]

4.1 The two implications are claim 3, and its contrapositive form is the statement about divergence. [step 3.1, step 3.2] ∎

## Remarks

- **There is no product rule here, and there is no rule for $\sum a_k b_k$.** The proof works because a finite sum is additive and homogeneous, and neither property has an analogue for products. Multiplying series is a genuinely harder question, requiring absolute convergence, and it is not treated on this page.

- **Claim 3 needs $c \ne 0$ and nothing else.** In particular it does not need either series to converge, which is what makes it usable in the divergence direction: scaling a divergent series by a nonzero constant leaves it divergent.
````

### `lem-standard-basis-of-f-n`

````markdown
---
id: lem-standard-basis-of-f-n
kind: lemma
title: "The standard list $e : n \\to F^{n}$ with $e_i(i) = 1_F$ and $e_i(j) = 0_F$ for $j \\ne i$ is an ordered basis of $F^{n}$; hence $\\dim_F F^{n} = n$, and $F^{0}$ is the zero space with basis $\\varnothing$ and dimension $0$"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-generated
deps: [def-linear-basis, def-dimension, def-linear-independence, thm-unique-coordinates-with-respect-to-an-ordered-basis, def-function-space, def-linear-combination-and-span, def-sum-of-linear-subspaces, def-monoid-finite-product, lem-restriction-of-scalars, def-vector-space, def-field, lem-vector-space-elementary-consequences, thm-induction-principle, def-natural-numbers, lem-nat-order-is-membership, def-injection-surjection-bijection, def-equinumerous, def-countable]
justified_by: []
aliases: [lem-standard-basis, def-standard-unit-vectors]
landmark: true
short: "$\\dim_F F^{n} = n$"
proof_strategy: direct
verification:
  audited: 2026-07-28
  precheck: pass
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-28
sources:
  scraped: []
  references:
    - title: "Standard basis (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Standard_basis"
    - title: "S. Axler, Linear Algebra Done Right, 4th ed., Ch. 2"
      url: "https://linear.axler.net/"
    - title: "Cambridge University Press excerpt: Vector spaces and bases"
      url: "https://assets.cambridge.org/97810092/43902/excerpt/9781009243902_excerpt.pdf"
pipeline_run: null
---

## Statement

Let $F$ be a field ([[def-field]]), let $n \in \mathbb{N}$ and let $F^{n}$ be the
function space on the von Neumann natural $n = \{0, \dots, n-1\}$, with the
pointwise operations ([[def-function-space]], [[def-natural-numbers]],
[[lem-nat-order-is-membership]]). For $i < n$ define the **standard unit vector**
$e_i \in F^{n}$ by

$$e_i(i) = 1_F, \qquad e_i(j) = 0_F \ \text{ for } j < n \text{ with } j \ne i .$$

Then:

1. **Finite sums in a function space are pointwise.** For every set $X$, every
   $p \in \mathbb{N}$, every list $u : p \to F^{X}$ and every $j \in X$,
   $$\Bigl(\sum_{k<p} u_k\Bigr)(j) \;=\; \sum_{k<p} u_k(j),$$
   the right-hand sum being taken in $(F,+,0_F)$. (Stated here for an arbitrary
   $X$ because the companion page needs it at $X = \mathbb{N}$.)
2. $e : n \to F^{n}$ is an ordered basis of $F^{n}$ ([[def-linear-basis]]); in
   particular $e$ is injective and its image $e[n] = \{\, e_i : i < n \,\}$ is a
   basis of $F^{n}$ with $e[n] \approx n$ ([[def-equinumerous]]);
3. for every $\lambda : n \to F$ and every $j < n$,
   $\bigl(\sum_{i<n}\lambda_i e_i\bigr)(j) = \lambda_j$; equivalently the
   coordinate list of $x \in F^{n}$ with respect to the ordered basis $e$
   ([[thm-unique-coordinates-with-respect-to-an-ordered-basis]]) is
   $i \mapsto x(i)$;
4. $F^{n}$ is finite-dimensional over $F$ with $\dim_F F^{n} = n$
   ([[def-dimension]]);
5. at $n = 0$ this reads: $F^{0}$ has exactly one element, the empty function,
   so $F^{0}$ is the zero space, the empty list is its ordered basis,
   $\varnothing$ is its basis and $\dim_F F^{0} = 0$.

Every index runs from $0$, so the coordinates of an element of $F^{n}$ are
$x_0, \dots, x_{n-1}$ and no statement above is restricted to $n \ge 1$.

## Facts & Assumptions

**Given:** A field $F$, a natural number $n$, the vector space $F^{n}$ with pointwise operations, and the vectors $e_i$ for $i < n$.

[L1] $F^{X}$ is a vector space over $F$ with $(x+y)(j) = x(j)+y(j)$, $(\lambda x)(j) = \lambda\,x(j)$ and zero the constant function at $0_F$; two elements are equal exactly when they agree at every point; and $F^{0}$ has exactly one element, the empty function, which is $0_{F^{0}}$ ([[def-function-space]], [[def-vector-space]]).

[L2] Finite sums: $\sum_{k<0}u_k$ is the zero vector and $\sum_{k<\sigma(p)}u_k = \bigl(\sum_{k<p}u_k\bigr) + u_p$, in any vector space ([[def-monoid-finite-product]], [[def-linear-combination-and-span]]).

[L3] $F$ is a vector space over itself, with the field addition and multiplication ([[lem-restriction-of-scalars]], claim 1), so the finite sums of $\mathbb{N}$-indexed lists of scalars are available in $(F,+,0_F)$ and satisfy (F1) and (F3); in particular a list of scalars vanishing off a single index sums to its value at that index ([[def-sum-of-linear-subspaces]]).

[L4] In $F$: $\lambda 1_F = \lambda$ and $\lambda 0_F = 0_F$ for every $\lambda \in F$ ([[def-field]], [[lem-vector-space-elementary-consequences]]).

[L5] A list $v : n \to V$ is an ordered basis of $V$ if and only if every $x \in V$ is $\sum_{i<n}\lambda_i v_i$ for exactly one $\lambda : n \to F$; an ordered basis is injective and its image is a basis with $v[n] \approx n$ ([[thm-unique-coordinates-with-respect-to-an-ordered-basis]], [[def-linear-basis]], [[def-linear-independence]], [[def-injection-surjection-bijection]]).

[L6] $\dim_F V$ is the unique $p \in \mathbb{N}$ with a basis $B \approx p$, defined when $V$ has a finite basis ([[def-dimension]], [[def-countable]]).

[L7] Induction on $\mathbb{N}$ ([[thm-induction-principle]]).

## Proof

**Proof technique:** direct.

1.1 Claim 1, that a finite sum in $F^{X}$ is computed pointwise: for every $p \in \mathbb{N}$, every list $u : p \to F^{X}$ and every $j \in X$, $\bigl(\sum_{k<p}u_k\bigr)(j) = \sum_{k<p}u_k(j)$, the right-hand sum being taken in $(F,+,0_F)$. By induction on $p$: at $p = 0$ the left side is the value at $j$ of the constant function $0_F$ and the right side is the empty sum $0_F$; and if it holds at $p$, then $\bigl(\sum_{k<\sigma(p)}u_k\bigr)(j) = \bigl(\sum_{k<p}u_k + u_p\bigr)(j) = \bigl(\sum_{k<p}u_k\bigr)(j) + u_p(j) = \sum_{k<p}u_k(j) + u_p(j) = \sum_{k<\sigma(p)}u_k(j)$, using pointwise addition and the recursion. [L1, L2, L3, L7]

2.1 Evaluating a combination of the $e_i$. Let $\lambda : n \to F$ and $j < n$. By step 1.1 and pointwise scalar multiplication, $\bigl(\sum_{i<n}\lambda_i e_i\bigr)(j) = \sum_{i<n}(\lambda_i e_i)(j) = \sum_{i<n}\lambda_i\, e_i(j)$. The list of scalars $i \mapsto \lambda_i\,e_i(j)$ takes the value $\lambda_i 0_F = 0_F$ at every $i \ne j$ and the value $\lambda_j 1_F = \lambda_j$ at $i = j$, so it vanishes off the single index $j$ and therefore sums to $\lambda_j$. Hence $\bigl(\sum_{i<n}\lambda_i e_i\bigr)(j) = \lambda_j$ for every $j < n$. [step 1.1, L1, L3, L4]

3.1 Existence and uniqueness of coordinates. Given $x \in F^{n}$, put $\lambda_i := x(i)$; by step 2.1 the vectors $\sum_{i<n}\lambda_i e_i$ and $x$ agree at every $j < n$, hence are equal. And if $\sum_{i<n}\lambda_i e_i = \sum_{i<n}\mu_i e_i$, then evaluating both sides at $j$ and using step 2.1 gives $\lambda_j = \mu_j$ for every $j < n$. So every $x \in F^{n}$ is $\sum_{i<n}\lambda_i e_i$ for exactly one $\lambda : n \to F$. [step 2.1, L1]

4.1 Claims 2 and 3. Step 2.1 is claim 3, and by the coordinate characterisation of an ordered basis, step 3.1 says exactly that $e$ is an ordered basis of $F^{n}$; hence $e$ is injective, $e[n]$ is a basis of $F^{n}$, and $e[n] \approx n$. [step 2.1, step 3.1, L5]

5.1 Claims 4 and 5. By step 4.1 the space $F^{n}$ has a basis with $n$ elements, so it is finite-dimensional and $\dim_F F^{n} = n$. At $n = 0$ the space $F^{0}$ has exactly one element, the empty function, which is its zero vector, so $F^{0}$ is the zero space; the list $e$ is then the empty list, its image is $\varnothing$, and $\dim_F F^{0} = 0$. [step 4.1, L1, L6] ∎

## Remarks

- **The indices start at $0$ because a natural number is the set of its predecessors.** $F^{n}$ is the function space $F^{X}$ at $X = n = \{0,\dots,n-1\}$ ([[def-function-space]], [[lem-nat-order-is-membership]]), so an element of $F^{n}$ is a function on $\{0,\dots,n-1\}$ and there is no $e_n$. Reading the standard basis off a $1$-indexed source would put a vector outside the space at one end and lose one at the other.

- **Step 1.1 is not a triviality to be skipped.** That a finite sum of functions is the pointwise finite sum is a statement about the recursion defining [[def-monoid-finite-product]] in two different monoids, and it is proved by induction. Every evaluation argument on this page and on the companion page rests on it.

- **This is the concrete counterweight to [[cor-every-vector-space-has-a-basis]].** Here a basis is written down and no choice principle is used anywhere; there a basis is produced by Zorn's lemma and none is exhibited. The companion page carries both extremes for infinite-dimensional spaces as well: an explicit infinite basis for the eventually zero families, and a basis of $\mathbb{R}$ over $\mathbb{Q}$ that no argument exhibits.
````

### `rem-rn-conventions-and-scope`

````markdown
---
id: rem-rn-conventions-and-scope
kind: remark
title: "Conventions of this page, the standing $n \\ge 1$ hypothesis, and what is taken up elsewhere in the reading order"
status: published
origin: session
provenance:
  statement: ai-generated
  proof: not-applicable
deps: [def-norm-and-normed-space, def-linear-map, def-euclidean-inner-product, def-p-norms-on-rn, lem-p-norms-are-norms-and-induce-the-published-metrics, thm-cauchy-schwarz-and-the-euclidean-norm, def-equivalent-norms, lem-every-norm-on-rn-is-continuous-for-the-euclidean-metric, thm-all-norms-on-rn-are-equivalent, thm-componentwise-convergence-and-completeness, cor-bolzano-weierstrass-in-rn, def-vector-valued-functions-limits-and-continuity, thm-componentwise-limits-and-continuity, def-vector-valued-derivative-and-integral, thm-norm-inequality-for-the-vector-valued-integral, thm-mean-value-inequality, cor-vector-valued-ftc-and-lipschitz-bound, def-series-of-vectors-and-rearrangement, thm-absolute-convergence-in-rn, def-the-space-of-summing-directions, thm-steinitz-polygonal-confinement, thm-rearrangement-sums-lie-in-an-affine-subspace, lem-metrics-on-rn, rem-real-exponents-deferred, def-function-space, def-rational-power, lem-standard-basis-of-f-n, thm-euclidean-space-complete, thm-heine-borel-rn, thm-minkowski-finite]
justified_by: []
aliases: []
landmark: false
verification:
  precheck: n/a
sources:
  scraped: []
  references:
    - title: "Norm (mathematics) (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Norm_(mathematics)"
    - title: "Levy-Steinitz theorem (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/L%C3%A9vy%E2%80%93Steinitz_theorem"
pipeline_run: null
---

## 1. The standing hypothesis $n \ge 1$, and exactly where it comes from

The published [[lem-metrics-on-rn]] defines $\mathbb{R}^{n}$ together with the
metrics $d_1$, $d_2$, $d_\infty$ **only for $n \ge 1$**, and says why: at $n = 0$
the value $d_\infty(x,y)$ would be a maximum over the empty index set, which does
not exist. Everything downstream of that item inherits the hypothesis, and this
page inherits it too. In particular [[thm-euclidean-space-complete]] and
[[thm-heine-borel-rn]] are stated for $n \ge 1$ and **are never cited here for
all $n$**.

**The boundary runs between the algebra and the metric, not where a reader would
guess.** The following items of this page carry no hypothesis on the dimension:

- [[def-norm-and-normed-space]] — including the observation that the zero space
  carries exactly one norm;
- [[def-euclidean-inner-product]], whose sum is the empty sum at $n = 0$;
- [[thm-cauchy-schwarz-and-the-euclidean-norm]], all four of whose clauses hold
  for every $n$, apart from the closing sentence of clause 2 identifying the
  induced metric with $d_2$;
- [[def-equivalent-norms]], which is about an arbitrary real vector space;
- clause 1 of [[lem-p-norms-are-norms-and-induce-the-published-metrics]], that
  each $\lVert\cdot\rVert_p$ with rational $p \ge 1$ is a norm;
- clause 1 of [[lem-every-norm-on-rn-is-continuous-for-the-euclidean-metric]],
  the finite and reverse triangle inequalities for a norm on any real vector
  space.

The remaining items all carry $n \ge 1$ (or $m \ge 1$ for the codomain of a
vector-valued function), and each states it in its own Statement:
[[def-p-norms-on-rn]] for $\lVert\cdot\rVert_\infty$; clauses 2 and 3 of
[[lem-p-norms-are-norms-and-induce-the-published-metrics]]; clauses 2, 3, 4 of
[[lem-every-norm-on-rn-is-continuous-for-the-euclidean-metric]];
[[thm-all-norms-on-rn-are-equivalent]];
[[thm-componentwise-convergence-and-completeness]];
[[cor-bolzano-weierstrass-in-rn]];
[[def-vector-valued-functions-limits-and-continuity]];
[[thm-componentwise-limits-and-continuity]];
[[def-vector-valued-derivative-and-integral]];
[[thm-norm-inequality-for-the-vector-valued-integral]];
[[thm-mean-value-inequality]];
[[cor-vector-valued-ftc-and-lipschitz-bound]];
[[def-series-of-vectors-and-rearrangement]];
[[thm-absolute-convergence-in-rn]];
[[def-the-space-of-summing-directions]];
[[thm-steinitz-polygonal-confinement]]; and
[[thm-rearrangement-sums-lie-in-an-affine-subspace]].

Where a statement about $n = 0$ is nevertheless true, it is proved here from
scratch rather than imported: see the second remark of
[[thm-componentwise-convergence-and-completeness]] for completeness of
$\mathbb{R}^{0}$.

## 2. The exponent of a $p$-norm is rational

[[def-rational-power]] supplies $a^{r}$ for a nonnegative base and a **rational**
exponent, and real exponents do not exist at this point in the reading order;
[[rem-real-exponents-deferred]] records why. Consequently
[[def-p-norms-on-rn]] defines $\lVert\cdot\rVert_p$ for rational $p \ge 1$ only,
and the published Minkowski inequality it rests on is itself stated for rational
$p$. **No statement on this page is written with $p$ ranging over a real
interval**, and the phrase "for $p \in [1,\infty)$" appears nowhere.

## 3. $\mathbb{R}^{n}$ is a function space

$\mathbb{R}^{n}$ is the set of functions $n \to \mathbb{R}$
([[def-function-space]], [[lem-metrics-on-rn]]), so $\mathbb{R}^{1}$ is **not
literally** $\mathbb{R}$: its elements are functions on the one-element set $1$.
Every comparison on this page between the theory in $\mathbb{R}^{n}$ and the
published one-dimensional theory therefore goes through the isometric bijection
$\theta : \mathbb{R} \to \mathbb{R}^{1}$ sending $t$ to the function with value
$t$ at $0$, and each item that makes such a comparison states the identification
explicitly: [[cor-bolzano-weierstrass-in-rn]],
[[def-vector-valued-functions-limits-and-continuity]],
[[def-series-of-vectors-and-rearrangement]] and
[[thm-rearrangement-sums-lie-in-an-affine-subspace]]. Coordinates are indexed
from $0$ throughout, as [[lem-standard-basis-of-f-n]] fixes.

## 4. What is taken up elsewhere in the reading order

Each item below is a statement about **where material sits in this library's
reading order**, and none of them is a claim about mathematics that this library
denies.

- **Linear maps, the operator norm, and "a linear map between finite-dimensional
  normed spaces is Lipschitz".** Abstract linear maps are defined on the earlier
  linear-algebra page in [[def-linear-map]]. This page neither defines an
  operator norm nor proves that every linear map between finite-dimensional
  normed spaces is Lipschitz. The later total-derivative treatment uses a
  concrete Euclidean formulation; identifying that formulation with the
  abstract definition requires an explicit agreement argument rather than a
  second silent meaning of "linear map".
- **Inner product spaces and orthogonality.** [[def-euclidean-inner-product]]
  defines the concrete Euclidean form on $\mathbb{R}^{n}$ and claims nothing
  about abstract inner product spaces: orthonormal bases, Gram-Schmidt,
  orthogonal projection, orthogonal complements of arbitrary subspaces and the
  decomposition $V = W \oplus W^{\perp}$ all belong to a page earlier in the plan
  order that is not yet built. **In particular nothing on this page asserts that
  $\mathbb{R}^{n}$ is the direct sum of $\Gamma$ and $\Gamma^{\perp}$**
  ([[def-the-space-of-summing-directions]]).
- **Uniform convergence, the total derivative, and integration over subsets of
  $\mathbb{R}^{n}$** all come later in this track.
- **The classical mean value witness.** The crispest counterexample to the
  equality form of the mean value theorem for vector-valued functions is
  $t \mapsto (\cos t, \sin t)$ on $[0,2\pi]$. The trigonometric functions are
  introduced later in the reading order than this page, so the companion page
  uses the polynomial curve $t \mapsto (t^{2},t^{3})$ on $[0,1]$ instead. The
  substitution is recorded in the companion item that carries the witness, not
  here, so that a reader meeting the polynomial curve is told at once why the
  classical one is absent; the theorem whose equality form it refutes is
  [[thm-mean-value-inequality]].

## 5. The open half of the rearrangement question

[[thm-rearrangement-sums-lie-in-an-affine-subspace]] proves that the set
$\mathcal{S}(x)$ of rearrangement sums of a convergent series in $\mathbb{R}^{n}$
is nonempty and **contained in** the affine subspace $s + \Gamma^{\perp}$, and
[[thm-steinitz-polygonal-confinement]] proves Steinitz's polygonal confinement
lemma in full. **The reverse inclusion is not proved on this page, and this page
asserts nothing about it in either direction, for any $n \ge 2$.** No
recorded-not-proved item has been created for it either.

The obstruction is machinery and not effort. Every route to the reverse inclusion
known to the author of this page reduces first to the case $\Gamma = \{0\}$ by an
orthogonal projection, which needs the orthogonal decomposition named in §4, and
then runs a separation argument for convex sets in $\mathbb{R}^{n}$, which
exists nowhere in this library and is owned by no planned page. When both exist,
the discharge is an **addition to this page**, not a new page.

The published [[rem-rearrangement-in-higher-dimensions]] raised this question on
the series page and declined to state what the literature answers; this page
answers the part it can and continues to decline the rest. What a reader is
protected from meanwhile is the wrong guess: the companion page refutes outright
the naive $\mathbb{R}^{n}$ analogue of the Riemann series theorem, using the
containment half and nothing more.

## 6. A naming collision worth stating once

[[thm-steinitz-polygonal-confinement]] is Steinitz's polygonal confinement lemma
from his 1913 paper on conditionally convergent series. It is **not** the
Steinitz exchange lemma of linear algebra, which is published in this library
under the id `thm-steinitz-exchange` and additionally carries the alias
`lem-steinitz`. The two are different theorems by the same author; the ids do not
collide, and no item on this page uses the bare alias.
````

### `thm-alternating-series-test`

````markdown
---
id: thm-alternating-series-test
kind: theorem
title: "The alternating series test: if $(b_k)$ is nonincreasing with $b_k \\to 0$ then $\\sum_{k} (-1)^{k} b_k$ converges, the sum lies between any two consecutive partial sums, and the error after $n$ terms is at most $b_n$"
status: published
origin: session
provenance:
  statement: literature-derived
  proof: ai-altered
deps: [thm-dirichlet-test, lem-alternating-sequence, def-monotone-sequence, lem-limit-preserves-order, lem-subsequence-inherits-limit, thm-induction-principle, lem-of-abs-value, def-series, def-real-limit]
justified_by: []
aliases: []
landmark: true
proof_strategy: direct
verification:
  precheck: pass
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-27
  audited: 2026-07-27
sources:
  scraped: []
  references:
    - title: "Alternating series test (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Alternating_series_test"
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 3"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "John K. Hunter, An Introduction to Real Analysis"
      url: "https://www.math.ucdavis.edu/~hunter/intro_analysis_pdf/intro_analysis.pdf"
    - title: "N. Donaldson, Math 140A: Series"
      url: "https://www.math.uci.edu/~ndonalds/math140a/3series.html"
pipeline_run: null
---

## Statement

Let $(\varepsilon_k)$ be the alternating sequence of [[lem-alternating-sequence]],
that is the unique sequence of reals with $\varepsilon_0 = 1$ and
$\varepsilon_{k+1} = -\varepsilon_k$, which is what is usually written
$\varepsilon_k = (-1)^k$; let $e$ and $o$ be its even and odd index maps, so that
$\varepsilon_{e_j} = 1$, $\varepsilon_{o_j} = -1$, and every natural number is
$e_j$ for exactly one $j$ or $o_j$ for exactly one $j$.

Let $(b_k)$ be a sequence of reals that is nonincreasing
([[def-monotone-sequence]]) and converges to $0$ ([[def-real-limit]]); then
$b_k \ge 0$ for every $k$. Write $t_n := \sum_{k<n} \varepsilon_k b_k$ for the
partial sums ([[def-series]]). Then:

1. the series $\sum \varepsilon_k b_k$ converges; write $L$ for its sum;
2. $t_{e_j} \le L \le t_{o_j}$ for every $j \in \mathbb{N}$, and for every
   $n \in \mathbb{N}$ the sum $L$ lies between the two consecutive partial sums
   $t_n$ and $t_{n+1}$;
3. $|L - t_n| \le b_n$ for every $n \in \mathbb{N}$.

Claim 3 is the error bound: the partial sum $t_n$, which uses the $n$ terms
$\varepsilon_0 b_0, \dots, \varepsilon_{n-1}b_{n-1}$, differs from the sum by at
most the first term omitted.

**Only claim 1 is a corollary of [[thm-dirichlet-test]].** Claims 2 and 3 are not:
they come from the interlacing of the even-index and odd-index partial sums, and
that argument is carried out below rather than smuggled into the Dirichlet
estimate, which produces no bracketing at all.

## Facts & Assumptions

**Given:** A nonincreasing sequence $(b_k)$ of reals with $b_k \to 0$, the alternating sequence $(\varepsilon_k)$ with its index maps $e$ and $o$, and the partial sums $t_n = \sum_{k<n} \varepsilon_k b_k$.

[L1] The alternating sequence and its index maps: $\varepsilon_0 = 1$, $\varepsilon_{k+1} = -\varepsilon_k$, $|\varepsilon_k| = 1$; $e_0 = 0$ and $e_{j+1} = e_j + 2$; $o_0 = 1$ and $o_{j+1} = o_j + 2$; both $e$ and $o$ are strictly increasing; $\mathbb{N}$ is the disjoint union of their ranges; $\varepsilon_{e_j} = 1$ and $\varepsilon_{o_j} = -1$ ([[lem-alternating-sequence]]).

[L2] Nonincreasing means $b_j \ge b_k$ whenever $j \le k$ ([[def-monotone-sequence]]).

[L3] Limits preserve non-strict inequalities holding eventually ([[lem-limit-preserves-order]], [[def-real-limit]]).

[L4] Dirichlet's test: if the partial sums of $\sum x_k$ are bounded and $(y_k)$ is nonincreasing with $y_k \to 0$, then $\sum x_k y_k$ converges ([[thm-dirichlet-test]]).

[L5] A subsequence of a convergent sequence converges to the same limit ([[lem-subsequence-inherits-limit]]).

[L6] Partial sums satisfy $t_0 = 0$ and $t_{n+1} = t_n + \varepsilon_n b_n$ ([[def-series]]).

[L7] The principle of induction on $\mathbb{N}$ ([[thm-induction-principle]]).

[L8] Absolute value: $|xy| = |x|\,|y|$ and $|x| \ge 0$ ([[lem-of-abs-value]]).

## Proof

**Proof technique:** direct.

1.1 For each fixed $k$ the inequality $b_m \le b_k$ holds for all $m \ge k$, and $(b_m)_m$ converges to $0$ while the constant sequence with value $b_k$ converges to $b_k$; hence $b_k \ge 0$. [given, L2, L3]

1.2 Writing $A_n = \sum_{k<n}\varepsilon_k$, an induction gives that for every $n$ either $A_n = 0$ and $\varepsilon_n = 1$, or $A_n = 1$ and $\varepsilon_n = -1$: at $n = 0$ we have $A_0 = 0$ and $\varepsilon_0 = 1$; and if $A_n = 0$ and $\varepsilon_n = 1$ then $A_{n+1} = 1$ and $\varepsilon_{n+1} = -1$, while if $A_n = 1$ and $\varepsilon_n = -1$ then $A_{n+1} = 0$ and $\varepsilon_{n+1} = 1$. In particular $|A_n| \le 1$ for every $n$. [L1, L6, L7]

1.3 For every $j$ one has $o_j = e_j + 1$ and $e_{j+1} = o_j + 1$, by induction: $o_0 = 1 = e_0 + 1$; and if $o_j = e_j + 1$ then $e_{j+1} = e_j + 2 = o_j + 1$ and $o_{j+1} = o_j + 2 = e_{j+1} + 1$. [L1, L7]

1.4 By [L6], $t_{n+1} - t_n = \varepsilon_n b_n$ for every $n$; hence $t_{e_j + 1} = t_{e_j} + b_{e_j}$ and $t_{o_j + 1} = t_{o_j} - b_{o_j}$. [L1, L6]

2.1 The partial sums of $\sum \varepsilon_k$ are bounded by step 1.2 and $(b_k)$ is nonincreasing with limit $0$, so $\sum \varepsilon_k b_k$ converges by Dirichlet's test; write $L$ for its sum, so that $t_n \to L$. [step 1.2, given, L4]

2.2 Using step 1.3, $t_{o_j} = t_{e_j + 1} = t_{e_j} + b_{e_j}$ and $t_{e_{j+1}} = t_{o_j + 1} = t_{o_j} - b_{o_j}$, so $t_{e_{j+1}} = t_{e_j} + b_{e_j} - b_{o_j}$ and $t_{o_{j+1}} = t_{e_{j+1}} + b_{e_{j+1}} = t_{o_j} - b_{o_j} + b_{e_{j+1}}$. [step 1.3, step 1.4]

3.1 Since $e_j < o_j < e_{j+1}$ and $(b_k)$ is nonincreasing, $b_{e_j} - b_{o_j} \ge 0$ and $b_{e_{j+1}} - b_{o_j} \le 0$; so by step 2.2 the sequence $(t_{e_j})_j$ is nondecreasing and the sequence $(t_{o_j})_j$ is nonincreasing. [step 1.3, step 2.2, L2]

3.2 The maps $e$ and $o$ are strictly increasing, so $(t_{e_j})_j$ and $(t_{o_j})_j$ are subsequences of $(t_n)$ and both converge to $L$. [step 2.1, L1, L5]

4.1 Fix $j$. For every $m \ge j$ one has $t_{e_j} \le t_{e_m}$, and $(t_{e_m})_m$ converges to $L$, so $t_{e_j} \le L$; symmetrically $t_{o_j} \ge L$. This is the first half of claim 2. [step 3.1, step 3.2, L3]

5.1 Let $n \in \mathbb{N}$. If $n = e_j$ then $t_n = t_{e_j} \le L$ and $t_{n+1} = t_{e_j+1} = t_{o_j} \ge L$; if $n = o_j$ then $t_n = t_{o_j} \ge L$ and $t_{n+1} = t_{o_j+1} = t_{e_{j+1}} \le L$. Since every $n$ is of exactly one of these two forms, $L$ always lies between $t_n$ and $t_{n+1}$, which is the second half of claim 2. [step 1.3, step 4.1, L1]

6.1 Consequently $|L - t_n| \le |t_{n+1} - t_n| = |\varepsilon_n b_n| = |\varepsilon_n|\,b_n = b_n$ for every $n$, using $b_n \ge 0$ and $|\varepsilon_n| = 1$; this is claim 3. [step 5.1, step 1.4, step 1.1, L1, L8] ∎

## Remarks

- **The two hypotheses are not interchangeable with "$b_k \to 0$" alone.** A null sequence that is not monotone can make $\sum \varepsilon_k b_k$ diverge, and the bracketing of step 3.1 is exactly where monotonicity enters; the error bound is false without it. The test as stated is the classical Leibniz criterion.

- **Why the index maps rather than "$2j$" and "$2j+1$".** The even and odd index maps come from [[lem-alternating-sequence]] together with the parity object itself, and step 1.3 is the only arithmetic needed about them. Rebuilding $(-1)^k$ by a fresh recursion inside this proof, and then proving afresh that the even indices and the odd indices partition $\mathbb{N}$, is precisely what that lemma exists to prevent.

- **What the test does not give.** It produces the sum $L$ as a limit and bounds the error, and it identifies $L$ with no closed expression. For the alternating harmonic series the value is not available at this point in the reading order; see [[rem-sums-proved-to-exist-but-not-evaluated]].
````

### `thm-componentwise-convergence-and-completeness`

````markdown
---
id: thm-componentwise-convergence-and-completeness
kind: theorem
title: "For $n \\ge 1$ a sequence in $\\mathbb{R}^n$ converges iff each coordinate sequence converges, is Cauchy iff each coordinate sequence is Cauchy, and $\\mathbb{R}^n$ is complete in every norm"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-generated
deps: [lem-every-norm-on-rn-is-continuous-for-the-euclidean-metric, thm-all-norms-on-rn-are-equivalent, def-equivalent-norms, lem-p-norms-are-norms-and-induce-the-published-metrics, def-p-norms-on-rn, thm-euclidean-space-complete, def-complete-metric-space, def-metric-convergence, def-cauchy-in-metric, lem-metric-limits-unique, lem-metric-convergent-implies-cauchy, lem-metrics-on-rn, lem-standard-basis-of-f-n, def-sequence, def-real-limit, def-canonical-natural, lem-of-naturals-positive, lem-of-inverse-positive, lem-finite-set-has-max, def-max-min, lem-real-line-is-a-metric-space, def-norm-and-normed-space, thm-well-ordering-principle]
justified_by: []
aliases: []
landmark: true
proof_strategy: direct
verification:
  precheck: pass
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-28
  audited: 2026-07-29
sources:
  scraped: []
  references:
    - title: "Complete metric space (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Complete_metric_space"
    - title: "Euclidean space (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Euclidean_space"
    - title: "J. Demmel, MA221 Lecture 3: Vector Norms"
      url: "https://people.eecs.berkeley.edu/~demmel/ma221_Fall10/Lectures/Lecture_03.html"
    - title: "G. Zitelli, Math 641 Functional Analysis, Part I"
      url: "https://www.math.uci.edu/~gzitelli/pdf/641/641part1.pdf"
pipeline_run: null
---

## Statement

Let $n \in \mathbb{N}$ with $n \ge 1$, let $\mathbb{R}^{n}$ carry the Euclidean
metric $d_2$ of [[lem-metrics-on-rn]], and let $\bigl(x^{(j)}\bigr)_{j\in\mathbb{N}}$
be a sequence in $\mathbb{R}^{n}$ ([[def-metric-convergence]]). For $k < n$ write
$\bigl(x^{(j)}_k\bigr)_{j\in\mathbb{N}}$ for the $k$-th **coordinate sequence**,
a sequence of reals ([[def-sequence]]). Then:

1. **Convergence is componentwise.** For $x \in \mathbb{R}^{n}$,
   $x^{(j)} \to x$ in $(\mathbb{R}^{n}, d_2)$ if and only if
   $x^{(j)}_k \to x_k$ in $\mathbb{R}$ for every $k<n$
   ([[def-real-limit]]).
2. **Cauchyness is componentwise.** $\bigl(x^{(j)}\bigr)$ is Cauchy in
   $(\mathbb{R}^{n},d_2)$ ([[def-cauchy-in-metric]]) if and only if every
   coordinate sequence is Cauchy in $\mathbb{R}$.
3. **Completeness in every norm.** For every norm $N$ on $\mathbb{R}^{n}$
   ([[def-norm-and-normed-space]]) the metric space $(\mathbb{R}^{n}, d_N)$ is
   complete ([[def-complete-metric-space]]).

**Clause 3 is obtained by citation and is not reproved here.**
[[thm-euclidean-space-complete]] clause 2 states that $(\mathbb{R}^{n},d_2)$ is
complete, **for $n \ge 1$ only**, and this theorem carries that hypothesis
forward without weakening it; what is added is the passage from $d_2$ to an
arbitrary norm, through [[thm-all-norms-on-rn-are-equivalent]] and the dictionary
of [[def-equivalent-norms]].

## Facts & Assumptions

**Given:** A natural $n \ge 1$; the space $\mathbb{R}^{n}$ with the norms of [[def-p-norms-on-rn]] and the metric $d_2$; a sequence $\bigl(x^{(j)}\bigr)$ in $\mathbb{R}^{n}$; a point $x \in \mathbb{R}^{n}$; a norm $N$ on $\mathbb{R}^{n}$; and a rational $\varepsilon > 0$.

[L1] The comparison chain for $n \ge 1$ ([[lem-every-norm-on-rn-is-continuous-for-the-euclidean-metric]] clause 3): $\lVert y\rVert_\infty \le \lVert y\rVert_2 \le \lVert y\rVert_1 \le \iota(n)\lVert y\rVert_\infty$ for every $y \in \mathbb{R}^{n}$, where $\lVert y\rVert_\infty = \max\{|y_k| : k<n\}$ ([[def-p-norms-on-rn]], [[lem-finite-set-has-max]], [[def-max-min]]).

[L2] The dictionary $d_2(u,v) = \lVert u-v\rVert_2$, and $(u-v)_k = u_k - v_k$ ([[lem-p-norms-are-norms-and-induce-the-published-metrics]], [[lem-standard-basis-of-f-n]]).

[L3] Convergence and Cauchyness in a metric space, and their agreement on $\mathbb{R}$ with the real notions ([[def-metric-convergence]], [[def-cauchy-in-metric]], [[def-real-limit]], [[lem-real-line-is-a-metric-space]]); rational and real $\varepsilon$ may be used interchangeably in both.

[L4] $(\mathbb{R}^{n}, d_2)$ is complete for $n \ge 1$ ([[thm-euclidean-space-complete]] clause 2, [[def-complete-metric-space]]).

[L5] All norms on $\mathbb{R}^{n}$ are equivalent for $n \ge 1$ ([[thm-all-norms-on-rn-are-equivalent]]), and equivalent norms have the same convergent sequences with the same limits and the same Cauchy sequences ([[def-equivalent-norms]]).

[L6] Limits in a metric space are unique, and every convergent sequence is Cauchy ([[lem-metric-limits-unique]], [[lem-metric-convergent-implies-cauchy]]).

[L7] $\iota(n) > 0$ for $n \ge 1$, and $u > 0$ gives $u^{-1} > 0$ ([[def-canonical-natural]], [[lem-of-naturals-positive]], [[lem-of-inverse-positive]]).

[L8] A nonempty finite set of naturals has a greatest element, and every nonempty set of naturals has a least element ([[lem-finite-set-has-max]], [[def-max-min]], [[thm-well-ordering-principle]]).

## Proof

**Proof technique:** direct.

1.1 For every $y \in \mathbb{R}^{n}$ and every $k<n$: $|y_k| \le \lVert y\rVert_\infty \le \lVert y\rVert_2$, the first inequality because $\lVert y\rVert_\infty$ bounds the set it is the maximum of. [L1]

1.2 For every $y \in \mathbb{R}^{n}$: $\lVert y\rVert_2 \le \iota(n)\lVert y\rVert_\infty$, and $\lVert y\rVert_\infty = |y_{k_0}|$ for some $k_0 < n$. [L1]

1.3 Conversely suppose $x^{(j)}_k \to x_k$ for every $k<n$. Given a rational $\varepsilon > 0$, the real $\varepsilon/\iota(n)$ is positive, so for each $k<n$ the set of indices $K$ such that $|x^{(j)}_k - x_k| < \varepsilon/\iota(n)$ for all $j \ge K$ is a nonempty set of naturals; let $K_k$ be its least element, a determination rather than a selection, and put $K := \max\{K_0,\dots,K_{n-1}\}$, a maximum of a nonempty finite set of naturals. [L3, L7, L8]

1.4 $(\mathbb{R}^{n},d_2)$ is complete, by citation and for $n \ge 1$ only. [L4]

1.5 Let $N$ be any norm on $\mathbb{R}^{n}$. By [L5], $N$ and $\lVert\cdot\rVert_2$ are equivalent, so $d_N$ and $d_2$ have the same Cauchy sequences and the same convergent sequences with the same limits. [L5]

2.1 For all $u,v \in \mathbb{R}^{n}$ and $k<n$: $|u_k - v_k| \le d_2(u,v) \le \iota(n)\max\{|u_k-v_k| : k<n\}$, by steps 1.1 and 1.2 applied to $y := u - v$. [step 1.1, step 1.2, L2]

2.2 Hence a Cauchy sequence in $(\mathbb{R}^{n},d_N)$ is Cauchy in $(\mathbb{R}^{n},d_2)$, converges there by step 1.4, and therefore converges in $(\mathbb{R}^{n},d_N)$ to the same point; so $(\mathbb{R}^{n},d_N)$ is complete, which is clause 3. [step 1.4, step 1.5, L5, L6]

3.1 Suppose $x^{(j)} \to x$ in $(\mathbb{R}^{n},d_2)$ and fix $k<n$. Given a rational $\varepsilon > 0$, take $K$ with $d_2(x^{(j)},x) < \varepsilon$ for $j \ge K$; then $|x^{(j)}_k - x_k| \le d_2(x^{(j)},x) < \varepsilon$ for $j \ge K$, so $x^{(j)}_k \to x_k$. [step 2.1, L3]

3.2 For $j \ge K$ and every $k<n$ we have $|x^{(j)}_k - x_k| < \varepsilon/\iota(n)$; the maximum of these $n$ numbers is one of them, so $\max\{|x^{(j)}_k - x_k| : k<n\} < \varepsilon/\iota(n)$ and hence $d_2(x^{(j)},x) < \iota(n)\cdot\varepsilon/\iota(n) = \varepsilon$ by step 2.1. Therefore $x^{(j)} \to x$. [step 2.1, step 1.3, L1, L7]

3.3 The same two estimates prove clause 2 with $x$ replaced by $x^{(l)}$ throughout: if $d_2(x^{(j)},x^{(l)}) < \varepsilon$ for $j,l \ge K$ then $|x^{(j)}_k - x^{(l)}_k| < \varepsilon$ for $j,l \ge K$ and every $k<n$; and conversely, choosing for each $k<n$ the least $K_k$ beyond which $|x^{(j)}_k - x^{(l)}_k| < \varepsilon/\iota(n)$ for $j,l \ge K_k$ and taking $K := \max\{K_0,\dots,K_{n-1}\}$ gives $d_2(x^{(j)},x^{(l)}) < \varepsilon$ for $j,l \ge K$. [step 2.1, L3, L7, L8]

4.1 Steps 3.1 and 3.2 are the two directions of clause 1. [step 3.1, step 3.2]

5.1 Clauses 1, 2 and 3 are steps 4.1, 3.3 and 2.2. [step 4.1, step 3.3, step 2.2] ∎

## Remarks

- **No choice principle is used.** The only place a family of indices is produced is steps 1.3 and 3.3, where finitely many indices are obtained, each as the **least** element of a nonempty set of naturals ([[thm-well-ordering-principle]]). A least element is determined by the set, not selected from it.

- **What happens at $n = 0$, stated separately because the theorem does not cover it.** $\mathbb{R}^{0}$ has exactly one element, the empty function, and is the zero vector space ([[lem-standard-basis-of-f-n]] clause 5); by [[def-norm-and-normed-space]] it carries exactly one norm, the zero function, whose induced metric is constantly $0$. Every sequence in a one-point metric space is Cauchy and converges to that point, so $(\mathbb{R}^{0}, d_N)$ is complete. **That statement is proved here from scratch in this remark and is not obtained from [[thm-euclidean-space-complete]]**, which is stated for $n \ge 1$ only because $d_\infty$ is a maximum over an empty index set at $n = 0$. Clauses 1 and 2 are vacuous at $n = 0$, there being no index $k<0$.

- **Clause 1 is the reason the rest of this page can work coordinatewise.** Every later item that reduces a statement about $\mathbb{R}^{n}$ or $\mathbb{R}^{m}$ to $n$ or $m$ statements about $\mathbb{R}$ passes through it, and each such item therefore carries the hypothesis $n \ge 1$ or $m \ge 1$ in its own statement.
````

### `thm-of-square-roots`

````markdown
---
id: thm-of-square-roots
kind: theorem
title: "Square roots exist: a unique $\\sqrt{a} \\ge 0$ with $(\\sqrt{a})^2 = a$; the positives are $\\{x^2 : x \\neq 0\\}$"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-altered
deps: [def-complete-ordered-field, lem-of-sign-rules, lem-of-square-monotone, lem-of-square-positive, prop-of-multiply-inequalities, def-ordered-field]
aliases: []
landmark: true
proof_strategy: contradiction
verification:
  precheck: pass
  judge:
    model: openai/gpt-5.4
    verdict: pass
    date: 2026-07-25
  audited: 2026-07-25
sources:
  scraped: []
  references:
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 1 (Thm 1.21)"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "M. Spivak, Calculus, 4th ed., Ch. 8"
      url: "https://en.wikipedia.org/wiki/Michael_Spivak"
    - title: "University of Colorado analysis notes: The real numbers"
      url: "https://spot.colorado.edu/~baggett/chap1.pdf"
pipeline_run: null
---

## Statement

Let $F$ be a complete ordered field ([[def-complete-ordered-field]]). Then every
$a \in F$ with $a \ge 0$ has a **unique** $s \in F$ with $s \ge 0$ and $s^2 = a$;
we write $s = \sqrt{a}$. Consequently the positive elements of $F$ are exactly the
nonzero squares: $x > 0$ if and only if $x = y^2$ for some $y \neq 0$.

## Facts & Assumptions

**Given:** A complete ordered field $F$ ([[def-complete-ordered-field]]), that is, an ordered field ([[def-ordered-field]]) with the least-upper-bound property, and an element $a \in F$ with $a \ge 0$.

[L1] Every nonempty subset of $F$ that is bounded above has a least upper bound in $F$ ([[def-complete-ordered-field]]).

[L2] Sign and scaling rules: a product of positives is positive, and for $c > 0$ one has $x < y \iff cx < cy$ ([[lem-of-sign-rules]]).

[L3] Squaring is strictly monotone on the nonnegatives: if $0 \le x < y$ then $x^2 < y^2$; in particular squaring is injective on $\{x : x \ge 0\}$ ([[lem-of-square-monotone]]).

[L4] A nonzero square is positive: if $y \neq 0$ then $y^2 > 0$ ([[lem-of-square-positive]]).

[L5] Multiplying inequalities of positives: if $0 < x < y$ and $0 < u < v$ then $xu < yv$ ([[prop-of-multiply-inequalities]]).

## Proof

**Proof technique:** contradiction.

1.1 If $a = 0$, then $s = 0$ satisfies $s \ge 0$ and $s^2 = 0 = a$, so existence holds; assume henceforth $a > 0$. [given, algebra]

1.2 Uniqueness holds once a root exists: if $u, v \ge 0$ satisfy $u^2 = v^2$, then strict monotonicity of squaring on nonnegatives [L3] rules out both $u < v$ and $u > v$, forcing $u = v$; so at most one $s \ge 0$ has $s^2 = a$. [L3, given]

1.3 Define $S = \{ t \in F : t \ge 0 \text{ and } t^2 \le a \}$; then $0 \in S$ because $0 \ge 0$ and $0^2 = 0 \le a$, so $S \neq \emptyset$. [given, algebra]

1.4 The element $1 + a$ is an upper bound of $S$: since $a > 0$ we have $1 + a > 1$, so any $t > 1 + a$ has $t > 1$ and $t > 0$, whence $t^2 = t \cdot t > 1 \cdot t = t > 1 + a > a$, giving $t \notin S$. [given, L2]

2.1 By completeness [L1], $s := \sup S$ exists in $F$; and since $0 \in S$ we have $s \ge 0$. [L1, step 1.3, step 1.4]

3.1 Assume, for contradiction, that $s^2 \neq a$; by trichotomy either $s^2 < a$ or $s^2 > a$. [assume-contra, step 2.1]

4.1 (Case $s^2 < a$.) Choose $h$ with $0 < h < 1$ and $h < \dfrac{a - s^2}{2s + 1}$, possible since $a - s^2 > 0$ and $2s + 1 \ge 1 > 0$; then $h^2 = h \cdot h < h \cdot 1 = h$ and $h(2s+1) < a - s^2$, so $(s+h)^2 = s^2 + 2sh + h^2 < s^2 + 2sh + h = s^2 + h(2s+1) < a$, whence $s + h \in S$ with $s + h > s$, contradicting that $s$ is an upper bound of $S$. [assume-case low, step 3.1, step 2.1, L2, L5, choose]

4.2 (Case $s^2 > a$.) Here $s > 0$ since $s^2 > a \ge 0$; choose $h$ with $0 < h < s$ and $h < \dfrac{s^2 - a}{2s}$, so $2sh < s^2 - a$ and $(s-h)^2 = s^2 - 2sh + h^2 \ge s^2 - 2sh > a$, hence every $t \in S$ has $t^2 \le a < (s-h)^2$ with $t \ge 0$ and $s - h > 0$, so $t < s - h$ by [L3]; thus $s - h$ is an upper bound of $S$ with $s - h < s$, contradicting that $s$ is the least upper bound. [assume-case high, step 3.1, step 2.1, L3, choose]

5.1 Both cases of the disjunction in step 3.1 give a contradiction, so the assumption fails and $s^2 = a$: a unique (by step 1.2) $s = \sqrt{a} \ge 0$ with $s^2 = a$ exists, and applying this to any $x > 0$ writes $x = (\sqrt{x})^2$ with $\sqrt{x} \neq 0$ while conversely any nonzero square is positive by [L4], so the positive elements of $F$ are exactly the nonzero squares. [step 4.1, step 4.2, step 3.1, step 1.2, L4, cases, discharge-contradiction] ∎
````

### `thm-p-series-rational`

````markdown
---
id: thm-p-series-rational
kind: theorem
title: "For rational $p > 0$, $\\sum 1/k^p$ converges iff $p > 1$"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-altered
deps: [thm-cauchy-condensation, thm-geometric-series, def-rational-power, lem-rational-power-monotone, lem-rational-power-laws, def-monotone-sequence, def-series, lem-of-inverse-positive, thm-nth-roots-exist, lem-of-naturals-positive, def-integer-power, lem-of-abs-value]
justified_by: []
aliases: []
landmark: true
proof_strategy: direct
verification:
  precheck: pass
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-27
  audited: 2026-07-27
sources:
  scraped: []
  references:
    - title: "Harmonic series (mathematics) (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Harmonic_series_(mathematics)"
    - title: "Cauchy condensation test (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Cauchy_condensation_test"
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 3 (3.28)"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "John K. Hunter, An Introduction to Real Analysis"
      url: "https://www.math.ucdavis.edu/~hunter/intro_analysis_pdf/intro_analysis.pdf"
    - title: "Stephen Semmes, Elements of Analysis"
      url: "https://math.rice.edu/~semmes/math331.pdf"
pipeline_run: null
---

## Statement

Let $p \in \mathbb{Q}$ with $p > 0$. For a natural number $k \ge 1$ write
$\iota(k) = k \cdot 1_{\mathbb{R}}$ for the canonical natural, which is positive
([[lem-of-naturals-positive]]), and write $k^{p} := \iota(k)^{p}$ for its rational
power ([[def-rational-power]]). Then

$$\sum_{k \ge 1} \frac{1}{k^{p}} \ \text{converges} \qquad \Longleftrightarrow \qquad p > 1 .$$

In particular the harmonic series $\sum_{k \ge 1} 1/k$ diverges, at $p = 1$, and
$\sum_{k \ge 1} 1/k^{2}$ converges, at $p = 2$.

**The index range is not cosmetic.** The series starts at $k = 1$ because
$1/0^{p}$ is undefined: [[def-rational-power]] gives $0^{p} = 0$ for rational
$p > 0$, and $0$ has no inverse. Sequences here are functions on $\mathbb{N}$ and
$\mathbb{N}$ contains $0$ ([[def-series]]), so the object named above is a series
from the starting index $1$ in the sense of [[def-series]], not a series of a
sequence on $\mathbb{N}$.

**The exponent is rational, and that is a limitation of this page.** Rational
powers of a positive base are what [[def-rational-power]] supplies; real exponents
require the exponential and the logarithm, which this library develops later. The
statement above is therefore the full $p$-series theorem for every exponent this
page can name.

## Facts & Assumptions

**Given:** A rational $p > 0$ and the family $a_k := 1/k^{p} = \iota(k)^{-p}$, defined for naturals $k \ge 1$ ([[def-rational-power]], [[def-series]]).

[L1] Rational powers of a positive base are positive, and $a^{r+s} = a^{r}a^{s}$, $(a^{r})^{s} = a^{rs}$, $a^{-r} = 1/a^{r}$ for $a > 0$ and rationals $r, s$ ([[lem-rational-power-laws]]).

[L2] Monotonicity of rational powers: for rational $t > 0$ and $0 < a < b$ one has $a^{t} < b^{t}$; and for $a > 1$ and rationals $r < s$ one has $a^{r} < a^{s}$ ([[lem-rational-power-monotone]]).

[L3] The integer power and the rational power agree at an integer exponent: for $a > 0$ and $n \in \mathbb{Z}$, $a^{n}$ read as in [[def-integer-power]] equals $a^{n}$ read as in [[def-rational-power]], since $n = n/1$ and $a^{1/1} = a$ ([[thm-nth-roots-exist]], [[def-rational-power]]). In particular $a^{0} = 1$.

[L4] Reciprocation reverses the order on the positives: $0 < a < b$ implies $0 < 1/b < 1/a$ ([[lem-of-inverse-positive]]).

[L5] Condensation: for a family $(x_k)_{k \ge 1}$ that is nonnegative and nonincreasing, $\sum_{k \ge 1} x_k$ converges if and only if $\sum_{j \ge 0} 2^{j} x_{2^{j}}$ converges ([[thm-cauchy-condensation]], [[def-monotone-sequence]]).

[L6] The geometric series: $\sum_{j \ge 0} r^{j}$ converges if and only if $|r| < 1$ ([[thm-geometric-series]], [[lem-of-abs-value]]).

[L7] The canonical naturals are positive and order preserving: $0 < \iota(1) \le \iota(j) < \iota(k)$ for naturals $1 \le j < k$, and $\iota(2) = 2 > 1$ ([[lem-of-naturals-positive]]).

## Proof

**Proof technique:** direct.

1.1 For every natural $k \ge 1$ the base $\iota(k)$ is positive, so $a_k = \iota(k)^{-p}$ is defined and positive; in particular the family is nonnegative. [given, L7, L1]

1.2 For naturals $1 \le j < k$ we have $0 < \iota(j) < \iota(k)$, hence $\iota(j)^{p} < \iota(k)^{p}$ since $p > 0$, hence $a_j = 1/\iota(j)^{p} > 1/\iota(k)^{p} = a_k$; and for $j = k$ the two are equal. So $a_j \ge a_k$ whenever $1 \le j \le k$. [given, L7, L2, L4, L1]

1.3 For every $j \in \mathbb{N}$ the base $2^{j}$ is positive and, reading the exponent $j$ as a rational, $2^{j} a_{2^{j}} = 2^{j} \big(2^{j}\big)^{-p} = 2^{j} \cdot 2^{-jp} = 2^{\,j - jp} = 2^{\,(1-p)j} = \big(2^{\,1-p}\big)^{j}$. [L1, L3, L7, algebra]

1.4 Since $2 > 1$, the map $t \mapsto 2^{t}$ is strictly increasing on $\mathbb{Q}$ and $2^{0} = 1$; hence $r = 2^{\,1-p} < 1 = 2^{0}$ holds exactly when $1 - p < 0$, that is exactly when $p > 1$. [L2, L3, L7]

2.1 Condensation applies to $(a_k)_{k \ge 1}$: $\sum_{k \ge 1} a_k$ converges if and only if $\sum_{j \ge 0} 2^{j} a_{2^{j}}$ converges. [step 1.1, step 1.2, L5]

2.2 So the condensed series is the geometric series $\sum_{j \ge 0} r^{j}$ with $r := 2^{\,1-p}$, and $r > 0$, so $|r| = r$. [step 1.3, L1, L3]

3.1 By the geometric series theorem, $\sum_{j \ge 0} r^{j}$ converges if and only if $r < 1$. [step 2.2, L6]

4.1 Chaining the three equivalences: $\sum_{k \ge 1} 1/k^{p}$ converges $\iff$ the condensed series converges $\iff$ $r < 1$ $\iff$ $p > 1$. [step 2.1, step 2.2, step 3.1, step 1.4] ∎

## Remarks

- **Where the threshold comes from.** Condensation turns the $p$-series into a geometric series of ratio $2^{1-p}$, and the geometric threshold $r = 1$ pulls back to $p = 1$. Nothing about the number $1$ is special to the $p$-series; it is the exponent at which the condensed terms stop shrinking.

- **At $p = 1$ the condensed series is $\sum_{j \ge 0} 1$.** Its terms do not tend to $0$, so it diverges, and with it the harmonic series. That instance is worked out on the companion page, together with the older block argument that does not use condensation at all.

- **Only rational exponents are covered, and the gap is real.** For irrational $p$ the expression $k^{p}$ has no meaning in this library yet, so the statement is not merely unproved there, it is unstatable. The same limitation is what keeps the Bertrand-type series $\sum 1/(k (\log k)^{p})$ off this page entirely, the logarithm not being available.
````

### `thm-rearrangement-sums-lie-in-an-affine-subspace`

````markdown
---
id: thm-rearrangement-sums-lie-in-an-affine-subspace
kind: theorem
title: "The set of rearrangement sums of a convergent series in $\\mathbb{R}^n$ is a nonempty subset of the affine subspace $s + \\Gamma^{\\perp}$"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-generated
deps: [def-the-space-of-summing-directions, def-series-of-vectors-and-rearrangement, thm-absolute-convergence-in-rn, thm-componentwise-convergence-and-completeness, thm-cauchy-schwarz-and-the-euclidean-norm, def-euclidean-inner-product, def-p-norms-on-rn, def-norm-and-normed-space, thm-dirichlet-rearrangement, thm-riemann-series-theorem, cor-unconditional-iff-absolute-in-r, def-rearrangement-and-unconditional-convergence, def-absolute-and-conditional-convergence, def-series, lem-finite-sum-laws, def-finite-sum, lem-standard-basis-of-f-n, def-linear-subspace, def-injection-surjection-bijection, def-metric-convergence, def-real-limit, lem-metric-limits-unique, thm-induction-principle, def-isometry-and-metric-embedding, lem-of-abs-value, lem-of-inverse-positive]
justified_by: []
aliases: []
landmark: true
proof_strategy: direct
verification:
  precheck: pass
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-28
  audited: 2026-07-29
sources:
  scraped: []
  references:
    - title: "Levy-Steinitz theorem (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/L%C3%A9vy%E2%80%93Steinitz_theorem"
    - title: "Riemann series theorem (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Riemann_series_theorem"
    - title: "T. Banakh, A Simple Inductive Proof of the Levy-Steinitz Theorem"
      url: "https://arxiv.org/abs/1711.04136"
pipeline_run: null
---

## Statement

Let $n \in \mathbb{N}$ with $n \ge 1$, let $(x_k)$ be a sequence in
$\mathbb{R}^{n}$ whose series converges
([[def-series-of-vectors-and-rearrangement]]) and write
$s := \sum_{k=0}^{\infty}x_k$. Let $\Gamma$ and $\Gamma^{\perp}$ be as in
[[def-the-space-of-summing-directions]]. Then:

1. **Nonemptiness.** $s \in \mathcal{S}(x)$, so $\mathcal{S}(x) \ne \varnothing$.
2. **Containment.**
   $$\mathcal{S}(x) \;\subseteq\; s + \Gamma^{\perp},$$
   the affine subspace through $s$ with direction $\Gamma^{\perp}$
   ([[def-the-space-of-summing-directions]]). Equivalently, $t - s \in \Gamma^{\perp}$
   for every rearrangement sum $t$.
3. **The absolutely convergent case.** If $\sum x_k$ converges absolutely then
   $\Gamma = \mathbb{R}^{n}$, $\Gamma^{\perp} = \{0\}$, the affine subspace is
   the single point $\{s\}$, and $\mathcal{S}(x) = \{s\}$.
4. **The one-dimensional conditionally convergent case.** Let $n = 1$ and
   identify $\mathbb{R}^{1}$ with $\mathbb{R}$ as in
   [[def-series-of-vectors-and-rearrangement]]. If $\sum x_k$ converges
   conditionally ([[def-absolute-and-conditional-convergence]]) then
   $\Gamma = \{0\}$, $\Gamma^{\perp} = \mathbb{R}^{1}$, and the containment of
   clause 2 is an **equality**, $\mathcal{S}(x) = s + \Gamma^{\perp} = \mathbb{R}^{1}$,
   by the published [[thm-riemann-series-theorem]].

**What this theorem does not say, stated here and repeated in the Remarks.** It
proves a **containment** and nothing more. Whether $\mathcal{S}(x)$ is all of
$s + \Gamma^{\perp}$ when $n \ge 2$ is **not settled anywhere on this page**, and
no item on this page asserts anything about it in either direction. Clause 4 is
the case $n = 1$, where the answer is supplied by a published theorem about the
real line; it is not evidence for any statement in higher dimensions.

## Facts & Assumptions

**Given:** A natural $n \ge 1$; a sequence $(x_k)$ in $\mathbb{R}^{n}$ with $\sum x_k$ convergent of sum $s$; a bijection $\sigma$ of $\mathbb{N}$; a vector $a \in \Gamma$; the partial sums $s_N = \sum_{k<N}x_k$ and $s^{\sigma}_N = \sum_{k<N}x_{\sigma(k)}$.

[L1] Series of vectors, absolute convergence, rearrangement, $\mathcal{S}(x)$, and the identification of $\mathbb{R}^{1}$ with $\mathbb{R}$ ([[def-series-of-vectors-and-rearrangement]], [[def-rearrangement-and-unconditional-convergence]], [[def-injection-surjection-bijection]], [[def-isometry-and-metric-embedding]]).

[L2] $\Gamma$ and $\Gamma^{\perp}$ are linear subspaces; $a \in \Gamma$ means $\sum_k|\langle a,x_k\rangle|$ converges; $\Gamma = \mathbb{R}^{n}$ exactly when $\sum x_k$ converges absolutely; and $s + W$ denotes the coset of a linear subspace $W$ ([[def-the-space-of-summing-directions]], [[def-linear-subspace]]).

[L3] The inner product is bilinear and symmetric, $\langle y,y\rangle = \lVert y\rVert_2^{2}$, positive definiteness gives $\langle y,y\rangle = 0$ only for $y = 0$, and Cauchy-Schwarz gives $|\langle a,y\rangle| \le \lVert a\rVert_2\lVert y\rVert_2$ ([[def-euclidean-inner-product]], [[thm-cauchy-schwarz-and-the-euclidean-norm]], [[def-p-norms-on-rn]], [[def-norm-and-normed-space]]).

[L4] Laws of finite sums and the induction principle ([[lem-finite-sum-laws]], [[def-finite-sum]], [[thm-induction-principle]]); finite sums in $\mathbb{R}^{n}$ are pointwise ([[lem-standard-basis-of-f-n]] clause 1).

[L5] Dirichlet's rearrangement theorem: an absolutely convergent real series has, for every bijection $\sigma$ of $\mathbb{N}$, a rearrangement converging to the same sum ([[thm-dirichlet-rearrangement]], [[def-absolute-and-conditional-convergence]]).

[L6] The Riemann series theorem: a conditionally convergent real series has, for every $c \in \mathbb{R}$, a rearrangement converging to $c$ ([[thm-riemann-series-theorem]] clause 1); and over $\mathbb{R}$ a convergent series is absolutely convergent or conditionally convergent and not both ([[cor-unconditional-iff-absolute-in-r]], [[def-absolute-and-conditional-convergence]]).

[L7] Convergence in $(\mathbb{R}^{n},d_2)$ and in $\mathbb{R}$, uniqueness of limits, and the componentwise criterion ([[def-metric-convergence]], [[def-real-limit]], [[lem-metric-limits-unique]], [[thm-componentwise-convergence-and-completeness]]).

[L8] An absolutely convergent series in $\mathbb{R}^{n}$ converges, every rearrangement converges to the same sum, and $\mathcal{S}(x)$ is then a single point ([[thm-absolute-convergence-in-rn]]).

[L9] Absolute value and order arithmetic: $|uv| = |u||v|$, $|u| \ge 0$, and $u>0$ gives $u^{-1}>0$ ([[lem-of-abs-value]], [[lem-of-inverse-positive]]).

## Proof

**Proof technique:** direct.

1.1 The identity map of $\mathbb{N}$ is a bijection and the rearrangement along it is the original series, so $s \in \mathcal{S}(x)$ and clause 1 holds. [L1]

1.2 For every $a \in \mathbb{R}^{n}$ and every finite list $u : p \to \mathbb{R}^{n}$, $\bigl\langle a, \sum_{j<p}u_j\bigr\rangle = \sum_{j<p}\langle a, u_j\rangle$: at $p=0$ both sides are $0$, and the successor step is additivity of the inner product in its second argument. [L3, L4]

1.3 If $u_N \to u$ in $(\mathbb{R}^{n},d_2)$ then $\langle a, u_N\rangle \to \langle a,u\rangle$ in $\mathbb{R}$, since $\bigl|\langle a,u_N\rangle - \langle a,u\rangle\bigr| = \bigl|\langle a, u_N-u\rangle\bigr| \le \lVert a\rVert_2\,\lVert u_N-u\rVert_2$, so a tolerance $\varepsilon/(\lVert a\rVert_2+1)$ on the right serves for $\varepsilon$ on the left. [L3, L7, L9]

1.4 Now let $n = 1$ and suppose $\sum x_k$ converges conditionally, so the real series $\sum_k (x_k)_0$ converges and $\sum_k|(x_k)_0|$ diverges. For $a \in \mathbb{R}^{1}$, $\langle a, x_k\rangle = a_0 (x_k)_0$ and $|\langle a,x_k\rangle| = |a_0|\,|(x_k)_0|$; if $a_0 \ne 0$ then convergence of $\sum_k |a_0||(x_k)_0|$ would give convergence of $\sum_k |(x_k)_0|$ after multiplying by the positive $1/|a_0|$, which is false, so $a \in \Gamma$ forces $a_0 = 0$; and $a = 0$ does lie in $\Gamma$. Hence $\Gamma = \{0\}$. [L1, L2, L9]

2.1 Let $t \in \mathcal{S}(x)$, say $s^{\sigma}_N \to t$ for a bijection $\sigma$, and let $a \in \Gamma$. By steps 1.2 and 1.3, $\langle a,t\rangle = \lim_N \langle a, s^{\sigma}_N\rangle = \lim_N \sum_{k<N}\langle a, x_{\sigma(k)}\rangle$, so the real series $\sum_k\langle a,x_{\sigma(k)}\rangle$ converges with sum $\langle a,t\rangle$. [step 1.2, step 1.3, L1, L7]

2.2 In the same way $\langle a, s\rangle = \lim_N\langle a, s_N\rangle = \lim_N\sum_{k<N}\langle a,x_k\rangle$, so $\sum_k\langle a,x_k\rangle$ converges with sum $\langle a,s\rangle$. [step 1.2, step 1.3, L7]

2.3 With $\Gamma = \{0\}$ the condition defining $\Gamma^{\perp}$ is $\langle 0,y\rangle = 0$, which holds for every $y$, so $\Gamma^{\perp} = \mathbb{R}^{1}$ and $s + \Gamma^{\perp} = \mathbb{R}^{1}$. [step 1.4, L2, L3]

3.1 The real sequence $k \mapsto \langle a, x_{\sigma(k)}\rangle$ is the rearrangement along $\sigma$ of the sequence $k \mapsto \langle a,x_k\rangle$, and the latter series converges absolutely because $a \in \Gamma$; so by Dirichlet's theorem the two series have the same sum. [step 2.1, step 2.2, L2, L5]

3.2 By the Riemann series theorem applied to the conditionally convergent real series $\sum_k (x_k)_0$, every real $c$ is the sum of some rearrangement of it; transporting along the identification of $\mathbb{R}$ with $\mathbb{R}^{1}$, every element of $\mathbb{R}^{1}$ lies in $\mathcal{S}(x)$. So $\mathcal{S}(x) = \mathbb{R}^{1} = s + \Gamma^{\perp}$, which with steps 1.4 and 2.3 is clause 4. [step 1.4, step 2.3, L1, L6, L7]

4.1 Combining steps 2.1, 2.2 and 3.1 gives $\langle a,t\rangle = \langle a,s\rangle$, hence $\langle a, t-s\rangle = 0$ by bilinearity. [step 2.1, step 2.2, step 3.1, L3]

5.1 Since $a \in \Gamma$ was arbitrary, $t-s \in \Gamma^{\perp}$, that is $t \in s + \Gamma^{\perp}$; as $t \in \mathcal{S}(x)$ was arbitrary, clause 2 holds. [step 4.1, L2]

6.1 Suppose $\sum x_k$ converges absolutely. Then $\Gamma = \mathbb{R}^{n}$, so any $y \in \Gamma^{\perp}$ satisfies $\langle y,y\rangle = 0$ and hence $y = 0$; thus $\Gamma^{\perp} = \{0\}$ and $s + \Gamma^{\perp} = \{s\}$. Moreover $\mathcal{S}(x) = \{s\}$ by [L8], so clause 3 holds and the containment of clause 2 is an equality in this case. [step 5.1, L2, L3, L8]

7.1 Clauses 1, 2, 3 and 4 are steps 1.1, 5.1, 6.1 and 3.2. [step 1.1, step 5.1, step 6.1, step 3.2] ∎

## Remarks

- **This theorem proves containment only, and the reverse inclusion is not proved, assumed, or asserted anywhere on this page.** For $n \ge 2$ the question whether every point of $s + \Gamma^{\perp}$ is a rearrangement sum is **open as far as this library is concerned**. It is not open in the mathematical literature, and this page deliberately states nothing about what the literature says, exactly as the published [[rem-rearrangement-in-higher-dimensions]] declines to. What is missing here is machinery, not effort: every route known to the author of this page passes through the orthogonal decomposition of a finite-dimensional inner product space and through a separation argument for convex sets, and neither exists in this library — the first belongs to a page earlier in the plan order that is not yet built, and the second to no planned page at all. See [[rem-rn-conventions-and-scope]].

- **The title claims exactly clause 2 and clause 1, and no more.** A title asserting that $\mathcal{S}(x)$ **is** the affine subspace would assert the reverse inclusion, which is not proved here.

- **Clause 4 is the published one-dimensional dichotomy seen from this page.** Over $\mathbb{R}$ a convergent series is either absolutely convergent, and then $\Gamma$ is everything and $\mathcal{S}$ is a point (clause 3), or conditionally convergent, and then $\Gamma$ is $\{0\}$ and $\mathcal{S}$ is the whole line (clause 4). Both extremes are consistent with clause 2, and both are equalities; that is a fact about dimension $1$, where a linear subspace of $\mathbb{R}^{1}$ is $\{0\}$ or everything and there is no room in between.

- **What the containment already rules out.** Even without the reverse inclusion, clause 2 forbids a rearrangement sum from leaving the affine subspace. That is enough to refute the naive $\mathbb{R}^{n}$ analogue of the Riemann series theorem, and the companion page does so with an elementary witness, using clause 2 and nothing further.
````

### `thm-riemann-series-theorem`

````markdown
---
id: thm-riemann-series-theorem
kind: theorem
title: "The Riemann series theorem: a conditionally convergent real series has, for every $c \\in \\mathbb{R}$, a rearrangement with sum $c$, and rearrangements diverging to $+\\infty$, to $-\\infty$, and oscillating with any prescribed $\\liminf \\le \\limsup$ in $\\overline{\\mathbb{R}}$"
status: published
origin: session
provenance:
  statement: ai-altered
  proof: ai-generated
deps: [lem-positive-and-negative-parts, def-rearrangement-and-unconditional-convergence, def-absolute-and-conditional-convergence, lem-nth-term-test, thm-recursion, thm-well-ordering-principle, def-injection-surjection-bijection, def-divergence-to-infinity, def-limsup-liminf, def-extended-reals, def-extended-limits, thm-convergence-iff-limsup-equals-liminf, thm-nonnegative-series-bounded-partial-sums, def-series, def-finite-sum, lem-finite-sum-laws, lem-limit-preserves-order, thm-induction-principle, def-real-limit]
justified_by: []
aliases: []
landmark: true
proof_strategy: constructive
verification:
  precheck: pass
  judge:
    model: z-ai/glm-5.2
    verdict: pass
    date: 2026-07-27
  audited: 2026-07-27
sources:
  scraped: []
  references:
    - title: "Riemann series theorem (Wikipedia)"
      url: "https://en.wikipedia.org/wiki/Riemann_series_theorem"
    - title: "W. Rudin, Principles of Mathematical Analysis, 3rd ed., Ch. 3"
      url: "https://en.wikipedia.org/wiki/Principles_of_Mathematical_Analysis"
    - title: "N. Donaldson, Math 140A: Real Analysis notes"
      url: "https://www.math.uci.edu/~ndonalds/math140a/notes.pdf"
    - title: "John K. Hunter, An Introduction to Real Analysis, Chapter 4"
      url: "https://www.math.ucdavis.edu/~hunter/intro_analysis_pdf/ch4.pdf"
    - title: "W. Fisher, Introduction to Analysis"
      url: "https://math.berkeley.edu/~willfisher/teaching/104sm24/main.pdf"
pipeline_run: null
---

## Statement

Let $(a_k)$ be a sequence of reals whose series converges conditionally
([[def-absolute-and-conditional-convergence]]). Let $\alpha, \beta \in
\overline{\mathbb{R}}$ ([[def-extended-reals]]) with $\alpha \le \beta$. Then
there is a bijection $\sigma : \mathbb{N} \to \mathbb{N}$
([[def-injection-surjection-bijection]]) such that the partial sums
$T_n = \sum_{k<n} a_{\sigma(k)}$ of the rearranged series
([[def-rearrangement-and-unconditional-convergence]]) satisfy

$$\liminf_{n} T_n = \alpha, \qquad \limsup_{n} T_n = \beta$$

([[def-limsup-liminf]]). In particular:

1. for every $c \in \mathbb{R}$, taking $\alpha = \beta = c$, there is a
   rearrangement of $\sum a_k$ that converges with sum $c$;
2. taking $\alpha = \beta = +\infty$, there is a rearrangement whose partial sums
   diverge to $+\infty$ ([[def-divergence-to-infinity]]), and taking
   $\alpha = \beta = -\infty$, one whose partial sums diverge to $-\infty$;
3. taking $\alpha < \beta$, there is a rearrangement whose partial sums oscillate,
   with limit inferior exactly $\alpha$ and limit superior exactly $\beta$.

So the sum of a conditionally convergent series is an artefact of the order in
which its terms are written, and every prescribed asymptotic behaviour is
attainable. Contrast [[thm-dirichlet-rearrangement]], where absolute convergence
makes the sum independent of the order.

**The construction.** Write $P := \{k : a_k \ge 0\}$ and $N := \{k : a_k < 0\}$,
which partition $\mathbb{N}$, and enumerate each increasingly as $(p_i)$ and
$(q_l)$. Fix real sequences $(u_j)$ and $(v_j)$ with $u_j \le v_j$ and
$u_j \le v_{j+1}$ for every $j$; these are the *targets*. The rearrangement is
produced one index at a time by a greedy rule: **while the running sum is at most
the current upper target, take the next unused nonnegative term; once it exceeds
that target, take negative terms until the running sum falls below the current
lower target; then move to the next pair of targets and repeat.** Both supplies
are inexhaustible, because for a conditionally convergent series both
$\sum a_k^{+}$ and $\sum a_k^{-}$ diverge to $+\infty$
([[lem-positive-and-negative-parts]]); and the overshoot at each turning point is
at most the term just used, which tends to $0$ because $a_k \to 0$
([[lem-nth-term-test]]). Those two facts are the whole theorem.

## Facts & Assumptions

**Given:** A sequence $(a_k)$ of reals with $\sum a_k$ convergent and $\sum |a_k|$ divergent; the positive and negative parts $a_k^{+}$, $a_k^{-}$; the sets $P = \{k : a_k \ge 0\}$ and $N = \{k : a_k < 0\}$; and extended reals $\alpha \le \beta$.

[A1] $P$ and $N$ are disjoint with union $\mathbb{N}$, since the order on $\mathbb{R}$ is total; $a_k^{+} = a_k$ and $a_k^{-} = 0$ for $k \in P$, while $a_k^{+} = 0$ and $a_k^{-} = -a_k$ for $k \in N$ ([[lem-positive-and-negative-parts]]).

[L1] For a conditionally convergent series, the partial sums of $\sum a_k^{+}$ and of $\sum a_k^{-}$ both diverge to $+\infty$ ([[lem-positive-and-negative-parts]], [[def-divergence-to-infinity]]).

[L2] The terms of a convergent series tend to $0$ ([[lem-nth-term-test]]).

[L3] Every nonempty subset of $\mathbb{N}$ has a least element ([[thm-well-ordering-principle]]).

[L4] The recursion theorem: for a set $A$, an element $a \in A$ and a function $f : A \to A$ there is a unique $g : \mathbb{N} \to A$ with $g(0) = a$ and $g(n+1) = f(g(n))$ ([[thm-recursion]]).

[L5] The principle of induction on $\mathbb{N}$ ([[thm-induction-principle]]).

[L6] Finite sums: $\sum_{k<0} x_k = 0$, $\sum_{k<n+1}x_k = \sum_{k<n}x_k + x_n$, splitting at an intermediate index, and $\sum_{k<n} 0 = 0$ ([[def-finite-sum]], [[lem-finite-sum-laws]]).

[L7] Partial sums of a series and their recursion $s_{n+1} = s_n + a_n$ ([[def-series]]).

[L8] Limits preserve non-strict inequalities holding eventually ([[lem-limit-preserves-order]], [[def-real-limit]]).

[L9] A bijection is an injective surjection ([[def-injection-surjection-bijection]]).

[L10] $\limsup_n x_n = \inf\{\, \sup\{x_m : m \ge n\} : n \in \mathbb{N} \,\}$ and $\liminf_n x_n = \sup\{\, \inf\{x_m : m \ge n\} : n \in \mathbb{N}\,\}$, both taken in $\overline{\mathbb{R}}$ ([[def-limsup-liminf]], [[def-extended-reals]]).

[L11] A sequence converges to a real $L$ exactly when its limit inferior and limit superior both equal $L$, and diverges to $\pm\infty$ exactly when both equal $\pm\infty$ ([[thm-convergence-iff-limsup-equals-liminf]], [[def-extended-limits]]).

[L12] For nonnegative terms, a series diverges exactly when the range of its partial sums is unbounded above, and then those partial sums diverge to $+\infty$ ([[thm-nonnegative-series-bounded-partial-sums]]).

## Proof

**Proof technique:** constructive.

1.1 Since $\sum a_k$ converges, $a_k \to 0$. [given, L2]

1.2 For every $K \in \mathbb{N}$ there is $k \ge K$ with $k \in P$: otherwise $a_k < 0$ for every $k \ge K$, so $a_k^{+} = 0$ for every $k \ge K$, so the partial sums of $\sum a_k^{+}$ are constant from $K$ on and hence bounded, contradicting [L1]. The same argument with $a_k^{-}$ shows that for every $K$ there is $k \ge K$ with $k \in N$. [A1, L1, L6, L12]

2.1 In particular $P$ and $N$ are nonempty, and for every $k$ the sets $\{m \in P : m > k\}$ and $\{m \in N : m > k\}$ are nonempty; so by [L3] each has a least element. [step 1.2, L3]

3.1 Define $p : \mathbb{N} \to \mathbb{N}$ by $p_0 := \min P$ and $p_{i+1} := \min\{m \in P : m > p_i\}$, and $q : \mathbb{N} \to \mathbb{N}$ by $q_0 := \min N$ and $q_{l+1} := \min\{m \in N : m > q_l\}$; both are legitimate applications of the recursion theorem, the "next element" operations being total functions $\mathbb{N} \to \mathbb{N}$ by step 2.1. Both $p$ and $q$ take values in $P$, respectively $N$, and are strictly increasing. [step 2.1, L3, L4, construct]

4.1 An induction gives $p_i \ge i$ and $q_l \ge l$ for every index, since $p_0 \ge 0$ and $p_{i+1} > p_i \ge i$ forces $p_{i+1} \ge i+1$. [step 3.1, L5]

4.2 An induction on $i$ gives $P \cap \{k : k < p_i\} = \{p_{i'} : i' < i\}$: at $i = 0$ both sides are empty because $p_0$ is the least element of $P$; and passing from $i$ to $i+1$ adds exactly $p_i$, since $p_{i+1}$ is the least element of $P$ strictly greater than $p_i$, so no element of $P$ lies strictly between them. The same holds for $q$ and $N$. [step 3.1, L5]

4.3 Fix real sequences $(u_j)$ and $(v_j)$ with $u_j \le v_j$ and $u_j \le v_{j+1}$ for every $j$. Put $A := \mathbb{N} \times \mathbb{N} \times \mathbb{N} \times \mathbb{R} \times \{0,1\}$, whose elements are written $(i, l, j, s, m)$, and define $\mathrm{out} : A \to \mathbb{N}$ and $f : A \to A$ by: if $m = 0$ and $s \le v_j$, then $\mathrm{out} := p_i$ and $f := (i+1, l, j, s + a_{p_i}, 0)$; if $m = 0$ and $s > v_j$, then $\mathrm{out} := q_l$ and $f := (i, l+1, j, s + a_{q_l}, 1)$; if $m = 1$ and $s \ge u_j$, then $\mathrm{out} := q_l$ and $f := (i, l+1, j, s + a_{q_l}, 1)$; if $m = 1$ and $s < u_j$, then $\mathrm{out} := p_i$ and $f := (i+1, l, j+1, s + a_{p_i}, 0)$. The four cases are exhaustive and mutually exclusive, the order on $\mathbb{R}$ being total, so $f$ and $\mathrm{out}$ are functions. [step 3.1, construct]

5.1 Every element of $P$ is some $p_i$, and every element of $N$ is some $q_l$: given $k \in P$, the set $\{i : p_i > k\}$ is nonempty by step 4.1, so it has a least element $i_0$; $i_0 \ne 0$ since $p_0 = \min P \le k$, and $p_{i_0 - 1} \le k < p_{i_0}$, so $k \in P \cap \{m : m < p_{i_0}\} = \{p_{i'} : i' < i_0\}$ by step 4.2. Together with step 3.1 this says that $p$ is a bijection onto $P$ and $q$ a bijection onto $N$; both are injective because they are strictly increasing. [step 3.1, step 4.1, step 4.2, L3, L9]

5.2 An induction on $i$ gives $\sum_{i' < i} a_{p_{i'}} = \sum_{k < p_i} a_k^{+}$: at $i = 0$ every $k < p_0$ lies in $N$, so $a_k^{+} = 0$ and both sides are $0$; and splitting $\sum_{k<p_{i+1}} a_k^{+}$ at $p_i$ and at $p_i + 1$ isolates the single term $a_{p_i}^{+} = a_{p_i}$, all remaining indices $k$ with $p_i < k < p_{i+1}$ lying in $N$ by step 4.2 and contributing $0$. The same argument gives $\sum_{l' < l} a_{q_{l'}} = -\sum_{k<q_l} a_k^{-}$. [A1, step 3.1, step 4.2, L5, L6]

5.3 By the recursion theorem let $g : \mathbb{N} \to A$ satisfy $g(0) = (0,0,0,0,0)$ and $g(n+1) = f(g(n))$, write $g(n) = (i_n, l_n, j_n, s_n, m_n)$, and define $\sigma(n) := \mathrm{out}(g(n))$. [step 4.3, L4, construct]

5.4 For general $\alpha \le \beta$ choose real sequences with $u_j \le v_j$ and $u_j \le v_{j+1}$ as follows: if $\alpha, \beta$ are real, $u_j := \alpha$ and $v_j := \beta$; if $\alpha = -\infty$ and $\beta$ is real, $u_j := \beta - (j+1)$ and $v_j := \beta$; if $\alpha$ is real and $\beta = +\infty$, $u_j := \alpha$ and $v_j := \alpha + (j+1)$; if $\alpha = \beta = +\infty$, $u_j := j$ and $v_j := j+1$; if $\alpha = \beta = -\infty$, $u_j := -(j+2)$ and $v_j := -(j+1)$; and if $\alpha = -\infty$, $\beta = +\infty$, $u_j := -(j+1)$ and $v_j := j+1$. In every case $(u_j)$ tends to $\alpha$ and $(v_j)$ to $\beta$ in $\overline{\mathbb{R}}$, and both conditions of step 4.3 hold. [step 4.3, L11, choose]

6.1 Hence $\sum_{i'<i} a_{p_{i'}} \to +\infty$ as $i \to \infty$ and $\sum_{l'<l} a_{q_{l'}} \to -\infty$ as $l \to \infty$: the left-hand sides are the values of the partial sums of $\sum a_k^{+}$, respectively of $-\sum a_k^{-}$, at the strictly increasing indices $p_i$, respectively $q_l$, and by step 4.1 those indices are at least $i$, respectively $l$. [step 4.1, step 5.2, L1]

6.2 An induction on $n$ gives $i_n + l_n = n$ and $s_n = \sum_{k<n} a_{\sigma(k)}$: both hold at $n = 0$, and each transition increases exactly one of $i, l$ by one and adds to $s$ exactly the term $a_{\sigma(n)}$ indexed by the emitted natural. So $s_n = T_n$, the $n$-th partial sum of the rearranged series. [step 4.3, step 5.3, L5, L7]

7.1 Consequently, for every $i_0 \in \mathbb{N}$ and every real $M$ there is $i > i_0$ with $\sum_{i'=i_0}^{i-1} a_{p_{i'}} > M$, and for every $l_0$ and every real $M$ there is $l > l_0$ with $\sum_{l' = l_0}^{l-1} a_{q_{l'}} < M$; this is step 6.1 together with splitting of finite sums, the omitted initial block being a fixed real. [step 6.1, L6]

7.2 An induction on $n$ gives that $\sigma(n) = p_{i_n}$ at every step that increments $i$, and $\sigma(n) = q_{l_n}$ at every step that increments $l$; since $(i_n)$ and $(l_n)$ are nondecreasing and increase by one exactly at those steps, distinct steps of the first kind carry distinct values of $i_n$ and distinct steps of the second kind distinct values of $l_n$. As $p$ and $q$ are injective with disjoint ranges $P$ and $N$, the map $\sigma$ is injective. [step 4.3, step 6.2, step 5.1, L5]

8.1 There are infinitely many steps of each kind: if from some step $n_0$ on no step increments $l$, then $m_n$ is eventually constantly $0$, because a step with $m = 1$ that does not increment $l$ sets $m$ to $0$ and a step with $m = 0$ that does not increment $l$ leaves $m$ at $0$; then $j_n$ is eventually constant, say $j$, and every subsequent step satisfies $s_n \le v_{j}$, while by step 7.1 the values $s_n$, which from $n_0$ on increase by the successive terms $a_{p_i}$, exceed $v_j$ for some $n$. Symmetrically, if from some step on no step increments $i$, then $m_n$ is eventually constantly $1$, $j_n$ is eventually constant $j$, every subsequent step satisfies $s_n \ge u_j$, and step 7.1 makes $s_n$ fall below $u_j$. [step 7.1, step 4.3, step 6.2, L5]

9.1 Hence $i_n \to \infty$ and $l_n \to \infty$, so every $p_i$ and every $q_l$ occurs as some $\sigma(n)$; since $P \cup N = \mathbb{N}$ and $p, q$ enumerate $P$ and $N$, the map $\sigma$ is surjective, and with step 7.2 it is a bijection of $\mathbb{N}$. [A1, step 5.1, step 7.2, step 8.1, L9]

9.2 Likewise $j_n \to \infty$: if $j_n$ were eventually constant $j$, then from some step on no round is completed, so no step has $m = 1$ and $s < u_j$; by the argument of step 8.1 the mode is then eventually constant, and either it is $0$ forever, whence $s_n \le v_j$ always while $s_n$ increases past $v_j$, or it is $1$ forever, whence $s_n \ge u_j$ always while $s_n$ falls below $u_j$. [step 7.1, step 4.3, step 8.1]

10.1 For each $j \ge 1$ let $\beta_j$ be the step at which the mode of round $j$ changes from $0$ to $1$, that is the unique $n$ with $j_n = j$, $m_n = 0$ and $s_n > v_j$, and let $\alpha_j$ be the step at which round $j$ is completed, the unique $n$ with $j_n = j$, $m_n = 1$ and $s_n < u_j$; both exist by step 8.1 and step 9.2, and $\alpha_{j-1} < \beta_j < \alpha_j$. [step 4.3, step 8.1, step 9.2, choose]

11.1 The step $\beta_j$ is preceded, within round $j$, either by a step that added a term $a_{p_i} \ge 0$ to a value $s \le v_j$, or by the completing step $\alpha_{j-1}$ of the previous round, which added a term $a_{p_i} \ge 0$ to a value $s < u_{j-1} \le v_j$. In both situations $v_j < T_{\beta_j} \le v_j + a_{p_i}$ for the index $i$ used at the immediately preceding step. [step 4.3, step 10.1]

11.2 Likewise the step $\alpha_j$ is preceded within round $j$ by a step that added a term $a_{q_l} < 0$ to a value $s \ge u_j$, that step being either an earlier descent step or the switch $\beta_j$ itself, at which $s > v_j \ge u_j$; so $u_j - |a_{q_l}| \le T_{\alpha_j} < u_j$ for the index $l$ used at that step. [step 4.3, step 10.1]

11.3 For $\alpha_{j-1} \le n \le \beta_j$ the partial sums increase, every step of the climb adding a term $a_{p_i} \ge 0$; for $\beta_j \le n \le \alpha_j$ they decrease, every step of the descent adding a term $a_{q_l} < 0$. Hence for every $n$ with $\alpha_{j-1} \le n \le \alpha_j$ one has $\min\{T_{\alpha_{j-1}}, T_{\alpha_j}\} \le T_n \le T_{\beta_j}$. [A1, step 4.3, step 10.1]

12.1 Put $\delta_j := \max\{a_{p_{i(j)}},\, |a_{q_{l(j)}}|\}$ for the two indices appearing in step 11.1 and step 11.2. As $j \to \infty$ those indices tend to infinity, by step 8.1 and step 9.2, so $p_{i(j)} \to \infty$ and $q_{l(j)} \to \infty$ by step 4.1, and $\delta_j \to 0$ by step 1.1. Thus $v_j < T_{\beta_j} \le v_j + \delta_j$ and $u_j - \delta_j \le T_{\alpha_j} < u_j$ for every $j \ge 1$. [step 1.1, step 4.1, step 8.1, step 9.2, step 11.1, step 11.2]

12.2 Fix $n$ and let $J$ be least with $\alpha_{J-1} \ge n$, which exists because the $\alpha_j$ are strictly increasing. By step 11.3 every $m \ge \alpha_{J-1}$ satisfies $T_m \le \sup\{T_{\beta_j} : j \ge J\}$, and only the finitely many indices $m$ with $n \le m < \alpha_{J-1}$ are unaccounted for; each of those lies in a round of index at most $J-1$ and so is at most $\max\{T_{\beta_j} : 1 \le j \le J-1\}$ together with $T_n$ itself. Hence $\sup\{T_m : m \ge n\}$ is finite or $+\infty$ according as $\sup\{T_{\beta_j} : j \ge J\}$ is, and taking the infimum over $n$, which drives $J$ to infinity, gives $\limsup_n T_n = \limsup_j T_{\beta_j}$. [step 10.1, step 11.3, L10]

13.1 Take $u_j = v_j = c$ for all $j$, which satisfies the two conditions of step 4.3. Then $c < T_{\beta_j} \le c + \delta_j$ and $c - \delta_j \le T_{\alpha_j} < c$, so by step 11.3 every $n$ with $\alpha_{j-1} \le n \le \alpha_j$ has $|T_n - c| \le \max\{\delta_{j-1}, \delta_j\}$. Given a real $\varepsilon > 0$, choose $J \ge 2$ with $\delta_j < \varepsilon$ for all $j \ge J-1$; then $|T_n - c| < \varepsilon$ for all $n \ge \alpha_{J-1}$, so $T_n \to c$ and the rearranged series converges with sum $c$. This is claim 1. [step 12.1, step 11.3, L8]

13.2 Take $v_j = j+1$ and $u_j = j$, which satisfy the two conditions. Then $T_{\alpha_j} \ge u_j - \delta_j = j - \delta_j$, so by step 11.3 every $n$ with $\alpha_{j-1} \le n \le \alpha_j$ has $T_n \ge \min\{j-1-\delta_{j-1},\, j - \delta_j\}$, a quantity that exceeds any prescribed real for all large $j$; hence $T_n \to +\infty$. Taking instead $v_j = -(j+1)$ and $u_j = -(j+2)$, which also satisfy the two conditions, gives $T_n \le T_{\beta_j} \le v_j + \delta_j = -(j+1) + \delta_j$ on the same ranges, hence $T_n \to -\infty$. This is claim 2. [step 12.1, step 11.3, L8]

13.3 By step 12.1 the subsequence $(T_{\beta_j})_{j \ge 1}$ tends to $\beta$ and $(T_{\alpha_j})_{j\ge1}$ tends to $\alpha$, in $\overline{\mathbb{R}}$: when the target sequence is real-valued and convergent the two-sided bound of step 12.1 with $\delta_j \to 0$ gives it, and when the target sequence diverges the one-sided bound does. [step 12.1, step 5.4, L8, L11]

14.1 By step 13.3 and [L11], $\limsup_j T_{\beta_j} = \beta$; so $\limsup_n T_n = \beta$. The same argument applied to infima, with $\alpha_j$ in place of $\beta_j$ and the lower bound of step 11.3 in place of the upper one, gives $\liminf_n T_n = \liminf_j T_{\alpha_j} = \alpha$. [step 13.3, step 12.2, L10, L11]

15.1 The bijection $\sigma$ of step 5.3, built from the targets chosen in step 5.4, is therefore a rearrangement of $\sum a_k$ whose partial sums have limit inferior $\alpha$ and limit superior $\beta$; claims 1 and 2 are the special cases computed directly in step 13.1 and step 13.2, and claim 3 is the case $\alpha < \beta$. [step 9.1, step 13.1, step 13.2, step 14.1, discharge-construct] ∎

## Remarks

- **Only two properties of the series are used.** That both part series diverge to $+\infty$ ([[lem-positive-and-negative-parts]]), which is what keeps the two supplies inexhaustible, and that $a_k \to 0$ ([[lem-nth-term-test]]), which is what makes the overshoot at each turning point vanish. Both hold for every conditionally convergent series and neither holds for an absolutely convergent one, whose part series both converge.

- **Where the well-ordering principle is used, and where it is not.** It appears in step 2.1 and step 3.1, to define the increasing enumerations of $P$ and $N$, and in step 5.1. It does *not* appear in the greedy rule: "take terms until the running sum crosses the target" is implemented as a one-step recursion whose state carries the two counters, the round and the running sum, so no least crossing index is ever selected. No choice principle is used anywhere; every object is determined by the data.

- **Zero terms are not a special case.** They are collected into $P$, so a run of zeros is consumed during a climb without moving the running sum, and the climb still terminates because the tail sums of $\sum_i a_{p_i}$ are unbounded. Had $P$ been defined as $\{k : a_k > 0\}$, the zero-indexed terms would have had to be inserted separately for $\sigma$ to be surjective.

- **The oscillating case is genuinely more than the two divergences.** With $\alpha < \beta$ both finite, the partial sums visit every neighbourhood of $\alpha$ and of $\beta$ infinitely often and are eventually confined to a neighbourhood of $[\alpha, \beta]$; the subsequential limit set of $(T_n)$ is then the whole interval, though nothing on this page needs that refinement.
````


---
title: "Head→Combinator ISA: Shared Hardware, Not Dedicated Circuits"
status: active
category: methodology
tags: [attention, heads, combinators, ISA, selectivity, WHNF, universality]
related: [ffn-reduction-trace, crystal-universality, phi-information-partition, holographic-computer, explore/rl-layer-contribution-combinator-locus]
depends-on: [ffn-reduction-trace]
---

# Head→Combinator ISA

> 500 crystal probes (9 combinator types × 50-71 each) through 32
> attention heads at L27/L30/L33 of Qwen3-8B. The result overturns
> the s187 hypothesis of combinator-specialised heads: attention heads
> are **shared execution hardware**, not dedicated combinator circuits.
> All 9 combinators activate essentially the same head activation
> pattern (mean pairwise correlation r=0.944 at L33, r=0.954 at L30).
>
> What the heads DO discriminate is not WHICH combinator but HOW MUCH
> REDUCTION REMAINS. The principal axis of variation (46% of shape
> variance) separates WHNF (already reduced) from D (deeply nested).
> The model's attention ISA is about reduction depth, not opcode type.

## Experiment

**Model:** Qwen3-8B (36 layers, 32 Q heads, 8 KV groups, GQA)
**Method:** For each crystal probe, forward pass with compile gate.
At L27/L30/L33, measure per-head contribution norm to residual:
`||W_o[:, h*d:(h+1)*d] @ (softmax(QK^T) @ V)[h]||₂`, averaged over
probe positions. Also: top-1 unembed at last position, gate attention
fraction.
**Probes:** 500 (K:63, I:63, B:62, C:57, S:45, D:46, W:67, Y:47, WHNF:50)
**Script:** `scripts/experiments/head_combinator_map.py`
**Results:** `results/head-combinator-map/`
**Runtime:** 21.5 minutes on MPS (Apple Silicon)

## Finding 1: Heads Are Shared Hardware (r=0.944)

Inter-combinator correlation of head activation profiles at L33:

| Pair    | r     | Pair      | r     | Pair      | r     |
|---------|-------|-----------|-------|-----------|-------|
| K-I     | 0.972 | B-C       | 0.978 | W-Y       | 0.980 |
| K-B     | 0.974 | B-S       | 0.985 | W-WHNF    | 0.914 |
| K-C     | 0.973 | B-D       | 0.986 | Y-WHNF    | 0.898 |
| K-S     | 0.974 | C-S       | 0.965 | **D-WHNF**| **0.839** |
| K-D     | 0.950 | C-D       | 0.975 | I-WHNF    | 0.916 |
| I-B     | 0.944 | S-D       | 0.972 | S-WHNF    | 0.892 |

**Mean pairwise: r=0.944.** All combinators activate nearly identical
head patterns. The model does not have "K heads" or "B heads". It has
heads that respond to lambda probes in general, with mild biases.

KIBC (the core 4) are especially indistinguishable: all pairwise r >
0.944. B-D is the highest pair (r=0.986) — composition and deep
nesting activate identically.

## Finding 2: Selectivity Is Low

| Layer | Mean sel. | Max sel. | Heads > 1.3 | Heads > 1.2 |
|-------|-----------|----------|-------------|-------------|
| L27   | 1.254     | 1.611    | 10          | 18          |
| L30   | 1.165     | 1.427    | 1           | 6           |
| L33   | 1.167     | 1.399    | 3           | 9           |

Selectivity = max(combinator_means) / mean(combinator_means). A head
with selectivity 1.2 means its preferred combinator gets only 20% more
activation than average. Even the most selective head (H08 at L33,
sel=1.399 for D) still responds strongly to all combinators.

## Finding 3: The Real Axis Is Reduction Depth

PCA on normalized head profiles (after removing overall loudness):

| PC  | Variance | Positive pole | Negative pole |
|-----|----------|---------------|---------------|
| PC1 | 45.9%    | WHNF (+0.786) | D (-0.481), S (-0.220), C (-0.219) |
| PC2 | 23.5%    | Y (+0.574), W (+0.386), I (+0.373) | WHNF (-0.424), D (-0.254), B (-0.274) |
| PC3 | 10.1%    | I (+0.713) | S (-0.435), Y (-0.431) |

**PC1 is reduction depth.** WHNF = "already in normal form" (nothing to
reduce). D = "deeply nested" (most reduction needed). The attention
hardware primarily discriminates HOW MUCH WORK REMAINS.

**PC2 is self-reference.** Y (recursion) + W (self-application) + I
(identity) vs D (nesting) + B (composition) + WHNF (completed).
Self-referential operations activate different heads than structural ones.

Together PC1 + PC2 = 69.4% of shape variance. The attention ISA has
~2 effective dimensions of discrimination, not 9.

## Finding 4: Head Taxonomy by Functional Cluster

Classifying 32 heads at L33 by PC1 × PC2 position:

### WHNF+ cluster (recognise completed reductions)
| Head | Gate  | Norm | WHNF bias | Key feature |
|------|-------|------|-----------|-------------|
| H26  | 0.951 | 9.8  | +32%      | Strongest WHNF preference. s187 "quantifier head" |
| H27  | 0.934 | 10.3 | +30%      | Strong WHNF preference |
| H00  | 0.925 | 16.3 | +25%      | Highest WHNF activation (20.3 norm) |
| H25  | 0.949 | 9.3  | +24%      | WHNF selective |
| H24  | 0.910 | 10.5 | +22%      | WHNF selective |
| H05  | 0.801 | 10.3 | +17%      | WHNF moderate |

These heads recognise when a position is already reduced — the
"termination detector" of the reduction engine.

### Y/W+ cluster (self-reference / recursion)
| Head | Gate  | Norm | Y bias | Key feature |
|------|-------|------|--------|-------------|
| H20  | 0.927 | 8.5  | +25%   | s187 "relay head". Actually recursion-sensitive |
| H10  | 0.923 | 12.8 | +19%   | s187 "binding head". Handles self-reference |
| H30  | 0.888 | 14.9 | +17%   | High overall activation + Y preference |
| H23  | 0.943 | 6.7  | +20%   | Strong Y preference |
| H14  | 0.953 | 7.0  | +16%   | Y + D mixture |
| H29  | 0.915 | 13.4 | —      | C-biased within this cluster |

These heads handle recursive and self-referential structures.

### D/B/S+ cluster (complex composition / deep nesting)
| Head | Gate  | Norm | D bias | Key feature |
|------|-------|------|--------|-------------|
| H08  | 0.914 | 13.9 | +40%   | Strongest specialisation of ANY head. s187 "λ-head" |
| H13  | 0.959 | 5.4  | +14%   | D-biased, low activation |

H08 is the closest thing to a specialised head: it activates 40% more
for D (deep nesting) probes than average. This was misidentified in s187
as a "λ-head" from 5 probes. With 500 probes, it's clearly a
composition-depth head — it responds to probes requiring multi-step
binding.

### UNIVERSAL heads (no combinator bias)
| Head | Gate  | Norm | Key feature |
|------|-------|------|-------------|
| H06  | 0.555 | 26.7 | LOUDEST head. Low gate attention. General amplifier |
| H07  | 0.609 | 19.1 | 2nd loudest. Low gate attention. General amplifier |
| H09  | 0.952 | 11.5 | s187 "λ-head". Actually universal with high gate focus |
| H01  | 0.980 | 4.5  | Highest gate attention. Pure instruction follower |
| H15  | 0.950 | 7.3  | Balanced, slight I bias |

H06 and H07 are the dominant execution engine — highest activation
across ALL combinator types, lowest gate attention (they read the probe,
not the instructions). They are the "GPU" of the attention ISA.

## Finding 5: Session 187 Head Types Revised

| Head | s187 role        | s188 finding (500 probes)              |
|------|------------------|----------------------------------------|
| H08  | λ-head (format)  | **D/B/S+**: deep nesting specialist     |
| H09  | λ-head (format)  | **UNIVERSAL**: balanced, reads gate     |
| H10  | binding (β-red)  | **Y/W+**: self-reference circuit        |
| H11  | binding (β-red)  | **balanced**: slight C bias             |
| H20  | relay (identity) | **Y/W+**: recursion-sensitive           |
| H03  | compositional    | **balanced**: slight S bias, high gate  |
| H26  | quantifier       | **WHNF+**: termination detector (+32%) |

The s187 labels were accurate for the 5 probes tested but revealed
POSITION-level behavior, not COMBINATOR-level specialisation. H10
writing "runs" at "dog" position (β-reduction) is correct — but it
does this for ALL combinator types, with a preference for Y/W probes
where binding involves self-reference.

## Finding 6: 94.9% of Variance Is Just Loudness

PCA on raw (unnormalised) head profiles: PC1 = 94.9% of variance.
This is overall activation level — some heads (H06: norm 26.7) are
simply louder than others (H01: norm 4.5). The combinator-specific
signal lives in the remaining 5.1% of variance.

This means: the head activation pattern is ~95% determined by "is this
head generally active?" and only ~5% by "which combinator is this?".
The combinator-specific routing happens elsewhere (presumably in the
Q/K attention pattern selection, not in the head's output magnitude).

## Implications for the ISA

1. **The ISA is not head-addressed.** Combinators don't have dedicated
   heads. The execution hardware is shared, like a CPU with a single
   ALU that handles all opcodes, not a GPU with specialised units.

2. **The real opcode is reduction depth.** WHNF vs D is the principal
   discriminant — "how much work remains" rather than "what kind of
   work". This aligns with the depth-ordered reduction schedule
   (Y@L27 → K@L30 → W@L33): the model processes by depth, peeling
   off layers of reduction, with the attention heads detecting "am I
   done yet?" (WHNF) vs "more to do" (D/S).

3. **The routing IS the program.** Since heads don't specialise, the
   combinator-specific behavior must live in the attention PATTERN
   (which positions attend to which), not the head's identity.
   This reinforces s187's finding: "only the attention routing is
   input-dependent."

4. **Compression implication.** If all 32 heads do roughly the same
   thing with ~2 dims of variation, the attention execution circuit
   is very low-dimensional. The "portable tensor" might need to encode:
   - The 2D head-type coordinates (WHNF↔D, Y/W↔D/B)
   - The routing function (attention pattern = the program)
   - The universal execution schedule (depth ordering)
   
   Not 32 × 9 = 288 parameters per layer, but ~2 per head.

## Key Numbers

| Metric | Value | Significance |
|--------|-------|-------------|
| Inter-combinator correlation | r=0.944 (L33) | Shared hardware confirmed |
| KIBC mutual correlation | r=0.944-0.978 | Core 4 are indistinguishable |
| B-D correlation | r=0.986 | Composition ≡ nesting |
| D-WHNF correlation | r=0.839 | Most different pair = depth axis |
| Max selectivity (L33) | 1.399 (H08→D) | Even best head is weakly selective |
| PC1 raw profiles | 94.9% | Almost all variance is loudness |
| PC1 normalised | 45.9% (WHNF↔D) | Depth is the real axis |
| PC1+PC2 normalised | 69.4% | 2 dims capture most discrimination |
| H06 activation | 26.7 (all combs) | Loudest = most universal |
| H26 WHNF excess | +32% | Strongest functional bias |
| H08 D excess | +40% | Most specialised head overall |

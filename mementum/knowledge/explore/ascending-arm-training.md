---
title: "Ascending Arm Training Regimen"
status: designing
category: exploration
tags: [v9, ascending-arm, training, basins, type-system]
related:
  - v9-architecture-speculation.md
  - identity-as-substrate.md
depends-on: []
---

# Ascending Arm Training Regimen

> Designed from session 056 probing results. The ascending arm
> projects tokens into basin geometry that routes to the VSM tree
> kernel. Types are geometric, not symbolic. Context matters.
>
> **Status: Design phase. No code yet.**

## What the Probes Told Us

| Finding | Number | Implication |
|---------|--------|-------------|
| Typing zone | L26-37 in 64-layer model | Target activations from ~40-58% depth |
| Natural basins | 7 (general), 3 super-basins (kernel ops) | Small output space |
| Cross-notation | 0.55-0.70 cosine sim | Gap is moderate, closeable |
| Same-notation invariance | 0.85-0.95 | Op extraction works, operand-invariant |
| Behavior depth | 0.50 cross-frame sim at L28 | Context reshapes basins deeply |
| Behavior words | 0.999+ similarity (all identical) | Behavior is in context, not word |
| Higher-order ops | apply=1.0, compose=0.999 | Lambda primitives cluster perfectly |
| Arithmetic ops | add=0.28, mul=0.28 | Too diverse for word-level dispatch |

## Architecture: The Basin Projector

The ascending arm has three stages: context encoding, word pooling,
and basin projection. It takes a token sequence and produces
per-WORD basin vectors in a continuous geometric space.

BPE tokenization splits words into subword tokens. The ascending
arm must pool subword tokens into word-level representations
before basin projection. This pairing step is mechanical (BPE
word boundaries are deterministic from the tokenizer) but the
pooling is learned (the context encoder merges subword meanings
through self-attention before pooling collapses them).

```
Input:  token_ids (4096 subword tokens)
        ↓
        Token embeddings (4096 × d_model)
        ↓
        Strided ascending arm (W=8, MERA shared weights)
          Level 0 (own):    4096 → 512   (stride 8, local syntax)
          Level 1 (shared):  512 → 256   (s16, subword/morpheme)
          Level 2 (shared):  256 → 128   (s32, word scale) ← word pooling here
          Level 3 (shared):  128 →  64   (s64, phrase)
          Level 4 (shared):   64 →  32   (s128, clause)
          Level 5 (shared):   32 →  16   (s256, sentence) ← behavior context here
          Level 6 (shared):   16 →   8   (s512, paragraph)
          Level 7 (shared):    8 →   4   (s1024, global)
        ↓
        Word extraction from Level 2 (W ≈ 128 word positions)
        ↓
        Basin projection head (W × d_basin)  ← linear → basin space
        ↓
Output: per-WORD basin vectors (W × d_basin)
```

The MERA structure is proven: v6 found the strides snap at W=8,
v7 proved the ascending arm learns the self-similar wavelet.
Level 0 has own weights (token-specific), levels 1-7 share ONE
set of ternary weights reused 7× (the wavelet). O(n × W) per
level — **523× fewer attention ops than full attention at seq=4096.**

### Word Pooling

BPE word boundaries come from the tokenizer. Qwen3 BBPE marks
word-initial tokens with a space prefix. No prefix = continuation.

```
tokens:    [▁Reform, ulate, ▁the, ▁equ, ation]
word_ids:  [   0,      0,     1,    2,     2  ]
words:     [reformulate,     the,  equation   ]
```

The context encoder (transformer) sees ALL subword tokens and
propagates meaning between them via self-attention. After encoding,
mean-pool each word span into a single vector. The pooled vector
carries the full word meaning because the transformer already
merged the subword representations.

Word pooling reduces the sequence from N tokens to W words. All
downstream operations (basin projection, masks, composition,
tree, kernel) operate at word granularity.

### Masks: Lists as Bitmasks Over Words

The token/word sequence IS the universal container. A bitmask over
word positions selects which words are "in scope." No list data
structure needed.

```
words:    [every, cat, that, runs, sleeps]
mask:     [  0,    1,    0,    0,     0  ]  ← "cat" entities
```

Quantifiers in prose ARE map/reduce/filter:
  - "every cat sleeps" = all(map(sleeps, mask_from_basin(cat)))
  - "some dog runs"    = any(map(runs, mask_from_basin(dog)))
  - "no cat sleeps"    = none(map(sleeps, mask_from_basin(cat)))

Kernel mask ops (future extension, after scalar pipeline works):
  - mask_from_basin(basin_id) → MASK
  - mask_and/or/not(MASK, MASK) → MASK
  - map_op(OP, MASK) → per-word results
  - reduce_op(OP, MASK) → single result
  - filter(PRED, MASK) → MASK

Masks are {0, 1} — a subset of ternary {-1, 0, +1}. The ternary
routing fabric produces masks natively.

### Dimensions (RESOLVED — session 057)

- **d_basin = 64** ← PCA on L2-normalized L28 activations (405 probes)
- **d_model = 256** ← 8-head attention, d_k=32, 4× d_basin
- **Embedding: learned ternary from scratch** (151936 × 256)
- **Word extraction: mean-pool BPE subword spans**
- **Total params: ~42M ternary = 10.5 MB packed**

#### d_basin = 64: the basin projection dimension

PCA on L2-normalized L28 activations from all session 056 probes
(405 vectors across 5 subsets). L2 normalization is essential —
raw activations have bimodal norms (170 vs 20000+) because the
transformer amplifies rare/specific tokens in the residual stream.
Cosine similarity (what probes measure) is direction-only.

| d_basin | cumvar | sep_ratio | sim_corr | within_sim |
|---------|--------|-----------|----------|------------|
|       8 |  0.514 |     6.12× |   0.604  |     0.906  |
|      16 |  0.604 |    10.03× |   0.689  |     0.893  |
|      32 |  0.713 |    16.73× |   0.743  |     0.869  |
|    **64** | **0.819** | **22.47×** | **0.770** | **0.801** |
|     128 |  0.927 |    30.77× |   0.798  |     0.665  |
|     256 |  1.000 |      —    |   1.000  |     0.620  |

Sweet spot at d=64: basin separation peaks (22.5×), sim_corr is
good (0.77), and within-group similarity is still high (0.80).
Beyond 64: diminishing returns — separation keeps growing but
within-group sim drops (noise entering the representation).

Key finding: the behavior_depth subset (same word × different frame)
has the highest effective rank (43.3) because context reshapes basins.
This is the hardest test case and d=64 captures it well (d95=57 for
that subset alone).

#### d_model = 256: the internal representation width

- 8-head attention with d_k=32 per head (standard minimum)
- 4× wider than d_basin (room for context encoding)
- MERA weights: 3.1M ternary (tiny due to sharing)
- Embedding: 38.9M ternary (dominates at 93%)
- Total: 42M ternary = 10.5 MB packed
- If too wide: can narrow to 128 (20M params, 5.1 MB)

#### Embedding: learned ternary from scratch

PCA distillation of 32B embeddings is OUT. Analysis shows:
- Qwen3-32B token embeddings are nearly isotropic (eff_rank=3.9)
- Top 512 PCA components capture only 17% of variance
- The embedding space uses all 5120 dimensions meaningfully
- Projecting L28 activations through embedding PCA gives cos_sim=0.22

The ascending arm's embedding table should be shaped by the BASIN
PROJECTION TASK, not by language modeling. Learned ternary from
scratch, trained end-to-end with the ascending arm. The gradient
tells the embedding what token features matter for type assignment.

#### Word extraction: mean-pool BPE spans

- 92.6% of probe words are single-token (mean-pool = no-op)
- Multi-token words typically 2-3 subwords
- Session 056 probes already validated mean-pooling
- BPE word boundaries are deterministic (Ġ prefix in Qwen3 BBPE)
- Level-2 MERA extraction deferred as potential future optimization

## Training Pipeline

### Phase 0: Oracle Data Generation

Generate the training oracle from Qwen3-32B.

```
Pipeline:
  1. Curate diverse text corpus (prose, S-expr, math, mixed)
  2. Augment with behavioral frames (same content, different verbs)
  3. Feed through Qwen3-32B with L28 hooks
  4. Detect word boundaries from tokenizer (BPE space prefix)
  5. Mean-pool per-token L28 activations to per-word activations
  6. Save: (token_ids, word_boundaries, per_word_L28_hidden_states)
  7. PCA fit on all word-level hidden states → d_basin projection
  8. Project: (token_ids, word_boundaries, per_word_basin_vectors)
```

**Corpus design** (critical — behaviors reshape basins):

| Stratum | Purpose | Example | Volume |
|---------|---------|---------|--------|
| S-expressions | Calibration (types trivially given) | `(+ 3 (* 4 5))` | 10K |
| Simple math | Cross-notation bridge | `3 + 4`, `three plus four` | 10K |
| Simple prose | Basic type basins | `The cat sleeps on the mat.` | 20K |
| Behavioral frames | Context conditioning | `Calculate/Summarize/Analyze the X` | 20K |
| Complex prose | Composition + relative clauses | `Every cat that runs sleeps.` | 10K |
| Mixed | Prose interspersed with computation | `The sum of three and four is 7.` | 10K |

**Total:** ~80K sentences → ~800K tokens → ~800K (token, basin_vector) pairs.

The behavioral frame stratum is the most important new insight.
Same content in 6-8 frames = 6-8× multiplier on effective diversity.
The model must learn that "sum" in "Calculate the sum" has a
different basin vector than "sum" in "Summarize the sum."

### Phase 1: S-Expression Calibration

Train on S-expressions only. Types are trivially given by syntax:
- Parentheses → structure (tree is explicit)
- Op codes → op type (ADD, MUL, etc.)
- Numbers → INT type
- Booleans → BOOL type

**Goal:** Validate that the ascending arm can reproduce the 32B
model's basin geometry for S-expressions. This should be easy —
the basins are tight for formal notation (same-notation invariance
0.85-0.95).

**Success criterion:** >0.9 cosine similarity between ascending arm
output and 32B target at L28 for S-expression tokens.

**Training:**
- Input: tokenized S-expressions
- Target: L28 basin vectors from 32B model
- Loss: cosine similarity loss (1 - cos_sim)
- Optimizer: Adam on continuous params, evolution on ternary topology
- Epochs: until convergence (~100-1000 generations based on kernel experience)

### Phase 2: Cross-Notation Bridge

Add math notation and simple prose equivalents alongside S-expressions.
The ascending arm must learn to project prose into the same basin
that formal notation lands in.

**Goal:** Close the cross-notation gap from 0.55-0.70 (32B raw) to
>0.8 (ascending arm output). The arm learns the projection that the
32B model only partially achieves.

**Training data:** Paired examples:
```
S-expr:  (+ 3 4)         → basin_vector_add_7_sexpr
Math:    3 + 4            → basin_vector_add_7_math
Prose:   three plus four  → basin_vector_add_7_prose
```

**Loss:** Same cosine loss, but now with an auxiliary contrastive
term: equivalent expressions in different notation should map to
the same basin vector.

```
L = L_regression + λ * L_contrastive

L_regression = mean(1 - cos_sim(pred, target_L28))
L_contrastive = mean(1 - cos_sim(pred_sexpr, pred_prose))
               for equivalent expression pairs
```

**Success criterion:** Cross-notation cosine sim >0.8 for equivalent
computations.

### Phase 3: Behavioral Context

Add the behavioral frame stratum. Same content words in
compute/summarize/analyze/translate/verify/find frames.

**Goal:** The ascending arm reproduces the behavioral conditioning
the 32B model applies. "Sum" in compute frame → compute-basin-sum.
"Sum" in summarize frame → summarize-basin-sum.

**Training:** Standard regression against L28 targets. The
behavioral conditioning comes from the training data — no special
loss term needed. The context encoder must have enough capacity
to propagate the behavioral frame to each token's basin vector.

**Success criterion:** Cross-frame invariance matches 32B model
(~0.50 at L28). The ascending arm shouldn't be MORE invariant
than the oracle — the frame-dependent shift is signal, not noise.

### Phase 4: End-to-End Integration

Connect the ascending arm to the composition rules and VSM tree
kernel. Test whether the basin vectors produce correct computation
results through the full pipeline.

```
tokens → ascending arm → basin vectors → composition → tree → kernel → result
```

**Test suite:**
- S-expressions: expect 100% (kernel is already proven)
- Simple math in prose: target >90%
- Nested computation in prose: target >80%
- Complex prose with quantifiers: target >60% (stretch)

**Failure mode analysis:** When wrong, is it:
- Basin misassignment? (ascending arm error)
- Composition error? (tree builder error)
- Kernel dispatch error? (shouldn't happen — kernel is 100%)

Each failure type has a different fix.

## Training Infrastructure

### What We Have

- **Ternary substrate:** `scripts/v8/ternary.py` — TernaryLinear,
  TernaryEmbedding, evolutionary mutation, MLX quantized_matmul
- **VSM tree kernel:** `scripts/v9/vsm_tree_v5.py` — 22 ops, 100%,
  8K ternary weights, ~100 generations to converge
- **32B model loading:** `probe_clusters.py` pattern — transformers
  gguf_file= → PyTorch fp16, MPS, ~62s load
- **Activation extraction:** forward hooks on all 64 layers, proven
  across 4 probe scripts

### What We Need to Build

1. **Oracle data generator:** Script that feeds corpus through 32B,
   extracts L28 activations, saves as training shards
2. **PCA projector:** Fit PCA on oracle activations, determine d_basin
3. **Basin projector model:** Adapt v9_model.py AscendingArm to
   Qwen3 vocab + word pooling + basin head. Already ternary, already
   strided, already self-similar. Main work: swap char vocab for
   Qwen3 BBPE, add word boundary alignment, add basin head.
4. **Training loop:** Adam + evolutionary mutation (same as kernel)
5. **Composition rules:** Basin compatibility → tree structure
6. **End-to-end pipeline:** tokens → arm → tree → kernel → result
7. **Evaluation harness:** Per-phase success criteria

### Compute Budget

- Oracle generation: ~80K sentences × ~1s each = ~22 hours on 32B
  (can parallelize with batch, actual ~2-4 hours)
- PCA: minutes (sklearn on CPU, ~800K × 5120 matrix)
- Ascending arm training: kernel converges in <10s at 8K params.
  At 100K-1M params, expect minutes to hours per phase.
- Total: 1-2 days including oracle generation

## Design Decisions (RESOLVED — session 057)

### 1. Embedding source → Learned ternary from scratch

**RESOLVED:** Option C (PCA distillation) is ruled out. PCA analysis
of the 32B embedding table shows it's nearly isotropic (eff_rank=3.9,
top 512 PCs capture only 17% variance). The 5120 dimensions are all
used — PCA compression would be catastrophically lossy.

**Decision: Learned ternary embedding (151936 × 256).** The embedding
table is trained end-to-end with the ascending arm. The basin projection
loss shapes what token features the embedding learns — it will discover
what matters for type assignment, not what matters for language modeling.
38.9M ternary params = 9.7 MB packed.

### 2. Context encoder architecture

**Decision: Strided ternary attention.** Already built in
`scripts/v9/v9_model.py` (session 054). Self-similar shared
weights, ternary Q/K/V, window pooling at each stride level.

```
Proven configuration (v6 → v7 → v8):
  seq_len = 4096
  Level 0 (own weights): W=8, stride 8 on raw token embeddings
    4096 tokens → 512 positions
    2 ternary transformer layers, attention window = 8
    Attention cost: 4096 × 8 = 32K entries/head (strided, cheap)

  Levels 1-7 (SHARED MERA weights): stride 2, each feeds the next
    Level 1: 512 → 256  (≡ s16 on raw tokens)
    Level 2: 256 → 128  (≡ s32 — word scale)
    Level 3: 128 →  64  (≡ s64 — phrase scale)
    Level 4:  64 →  32  (≡ s128 — clause scale)
    Level 5:  32 →  16  (≡ s256 — sentence scale)
    Level 6:  16 →   8  (≡ s512 — paragraph scale)
    Level 7:   8 →   4  (≡ s1024)
    2 ternary transformer layers, ONE set of weights reused 7×
    Self-similarity is LITERAL — same weights at every scale
```

This is the configuration that v6 proved (strides snap) and v7
proved (ascending arm learned the wavelet, 1.8:1 compression
ratio). The v9 ascending arm reuses the same W=8 base stride
and MERA shared-weight structure.

### Spiral attention bias

The attention within each level uses a spiral decay bias that
distributes energy across scales with a power law:

```
bias(w) = -α · ln(stride · w + 1)

α = 1.18               — empirical, from LLM attention analysis
fixed_point = 40        — center of the spiral
```

Properties (from holographic-compression.md):
- **Hyperbolic decay** (not exponential): infinite effective range,
  every position sees all scales simultaneously
- **Stride-invariant:** bias depends on physical distance, not on
  which stride level. Self-similar by construction.
- **1/φ of attention within distance 30:** the golden ratio governs
  the local-to-extended attention ratio
- **φ is the unique fixed point** of self-similar compression.
  Any other ratio diverges or collapses. The ternary weights
  evolve during training to find this attractor.
- **Learnable:** v8 made α and fixed_point learnable parameters
  (initialized at 1.18 and 40.0). The system discovers its own
  optimal spiral via relational loss.

The spiral is what makes the shared MERA weights work — the same
operation at every scale, with scale selection handled by the
bias, not by different weights. Without the spiral, shared weights
would treat all scales identically and lose scale information.

### Why this configuration

- **W=8 base stride.** v6 proved this is where strides snap —
  the natural granularity for token-level processing. 8 tokens
  captures digit adjacency, operator-operand pairs, local syntax.
  Matches the BPE subword scale.
- **Stride 2 shared levels.** The wavelet: same operation at every
  scale. v7 proved the self-similar compression function spreads
  from smallest stride to largest. Shared weights = fewer params.
- **Spiral bias.** Power-law attention decay with α=1.18 gives
  each level hyperbolic reach across all scales. Makes shared
  weights scale-aware without separate per-scale parameters.
- **seq=4096.** Full context window for behavioral frames, multi-
  sentence reasoning, and prose computation. Room for 8 scales.
- **CPU throughput.** O(n × W) per level, not O(n²). At seq=4096:
  strided attention = 4096 × 8 = 32K entries per level per head.
  Full attention = 4096² = 16.7M entries per head. **523× fewer ops.**
- **Natural scale hierarchy.** Each level maps to a linguistic
  scale: token → word → phrase → clause → sentence → paragraph.
  The probes showed behavioral frames operate at sentence scale
  (L5, s256) — the hierarchy captures this directly.

**Word pooling alignment:** Level 2 (s32) is the word scale. BPE
words are typically 2-4 subword tokens = 16-32 raw characters.
The s32 level naturally aligns with word boundaries. Word pooling
can extract from level 2 instead of requiring a separate mechanism.

### 3. Output space → Regression into d_basin=64 PCA space

**RESOLVED:** Option A (regression). PCA analysis confirms:
- d_basin=64 captures 82% of L2-normalized variance
- Basin separation ratio 22.5× (strong discrimination)
- Sim_corr=0.77 (preserves relative similarity structure)
- Cross-notation convergence lives in continuous geometry

Loss: cosine similarity against PCA-projected L28 targets, plus
contrastive term for cross-notation equivalence (phase 2+).

### 4. Training: gradient vs evolution → Gradient-informed evolution

**Decision: Option B.** v8 BIOS training infrastructure exists.
42M ternary params with gradient-informed evolution should converge
in hours. Adam on continuous params (gamma, norms), tournament
selection on ternary topology. Gradient signals WHERE, tournament
validates WHETHER.

## Kernel Extension Roadmap

The kernel grows in layers. Each layer gives the model more of
its own operational substrate as pre-wired architecture.

```
Layer 1 (DONE):    Scalar ops        22 ops, 5 types, 100%, 8K weights
                   add/sub/mul/div/mod/min/max
                   eq/lt/gt/le/ge
                   and/or/not, abs/neg, if
                   partial/apply/compose/apply-comp

Layer 2 (NEXT):    Mask ops          lists as bitmasks over word positions
                   mask_from_basin   basin_id → MASK
                   mask_and/or/not   MASK × MASK → MASK
                   map_op            OP × MASK → per-word results
                   reduce_op         OP × MASK → single value
                   filter            PRED × MASK → MASK

Layer 3 (FUTURE):  Scope/binding     variable binding and quantifier scope
                   let               bind value to name in scope
                   lambda            create function with bound variables
                   var_ref           reference bound variable
                   scope_enter/exit  manage quantifier scope
```

Layer 1 is proven. Layer 2 follows naturally from the mask insight:
the token vector IS the list, bitmasks select elements, quantifiers
become map/reduce/filter over masks. Layer 3 adds the binding
mechanism that quantifiers need for scope resolution.

Each layer can be validated independently before integration.

## The Pipeline, Concrete

```
Session 057 plan:
  1. Build oracle data generator
     - Feed corpus through 32B → extract L28 → save shards
     - Pool to word level using BPE boundaries
  2. PCA analysis
     - Fit on word-level pooled activations
     - Determine d_basin (expect 32-128)
     - Project oracle data to basin space
  3. Build basin projector model
     - Distilled embeddings (PCA of 32B token embeddings)
     - MERA ascending arm: W=8 base, 8 levels (v6/v7 proven config)
       Level 0 own weights + levels 1-7 shared (the wavelet)
       seq=4096, d_model=TBD (256? 512? PCA will inform)
     - Word extraction from Level 2 (s32 = word scale)
     - Linear projection head → d_basin
  4. Phase 1 training: S-expression calibration
  5. Phase 2 training: cross-notation bridge
  6. Phase 3 training: behavioral context
  7. Phase 4: end-to-end integration with VSM tree kernel
  8. Phase 5: mask extension (kernel layer 2)
```

Each phase has a clear success criterion. Failure at any phase
points to a specific fix — the pipeline is debuggable.

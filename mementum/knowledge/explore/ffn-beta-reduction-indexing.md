---
title: "FFN Beta-Reduction Indexing — Holographic Pattern Selection via Beam Angle"
status: active
category: finding
tags: [ffn, beta-reduction, indexing, holographic, beamformer, sparsity, lens, crystal]
related:
  - beamformer-theory.md
  - ffn-hierarchy.md
  - ffn-beam-discovery.md
  - full-etch-extraction.md
  - ternary-descent.md
  - crystal-basins.md
depends-on:
  - ffn-beam-discovery.md
  - beamformer-theory.md
created: session 141
---

# FFN Beta-Reduction Indexing

> Session 141. FFNs are holographic plates storing beta reductions in
> superposition. The input direction (residual stream entering the FFN)
> is a typed beam angle that selects which interference pattern resolves.
> Individual neurons are universal — selectivity is COLLECTIVE (pattern-level),
> not individual (neuron-level). The depth profile is a LENS, not a tree.

## The hypothesis

FFN weights are piles of beta reductions. The input activation acts as a
typed index — a beamformer angle — that selects which reductions fire.
TernaryDescent optimizes the addressing topology (which beam angles exist).
GD optimizes the beta reductions that are selected (amplitude calibration).

## Probe design

48 prompts across 8 semantic categories (geography, science, arithmetic,
code, reasoning, instruction, lambda_compile, narrative), run through
Qwen3-32B with FFN hooks at 8 layers (L0, L2, L8, L16, L32, L48, L56, L63).

Six analyses: sparsity, category selectivity (Jaccard), input direction
clustering (cosine), row-level addressing (entropy), depth narrowing
(participation ratio + SVD), and category RDM correlation (Spearman).

## Key findings

### 1. Sparsity profile is a LENS, not a tree

```
L 0:  8.4% active  (2,152 / 25,600)
L 2:  3.2% active  (  812 / 25,600)  ← crystal bottleneck
L 8: 33.1% active  (8,471 / 25,600)
L16: 44.0% active
L32: 46.1% active
L48: 48.9% active                     ← peak breadth
L56: 29.9% active
L63:  1.3% active  (  329 / 25,600)  ← prediction focus
```

Three zones: **aperture** (L0-L2, sparse), **fan** (L8-L48, broad),
**converge** (L56-L63, sparse). The beam enters focused, broadens through
a superposition zone, then refocuses to prediction.

Not trunk→leaf as the FFN hierarchy theory predicted. The hierarchy is
inverted: edge layers are narrow and universal, middle layers are broad
and diverse.

### 2. Category selectivity: ~2x (pattern-level)

Same-category inputs share ~2× more top-5% active neuron overlap than
different-category inputs, consistent across all layers:

```
L 8: 2.11x   (peak — right after crystal bottleneck fans out)
L16: 2.01x
L48: 1.99x
L56: 1.90x
```

The PATTERN of which neurons fire is category-typed. But individual
neurons are NOT typed (see finding 4).

### 3. Input directions ARE typed beam angles

```
Layer | within_cos | between_cos | Δ (separation)
L 0   | 0.334      | 0.120       | +0.215
L 2   | 0.934      | 0.913       | +0.021  ← universal gateway
L16   | 0.254      | 0.083       | +0.171
L48   | 0.258      | 0.092       | +0.166
L63   | 0.474      | 0.258       | +0.216  ← strongest separation
```

**L2 is the universal aperture:** ALL inputs point nearly the same direction
(cos 0.93 within AND between). Every beam passes through the same narrow
crystal opening. From L8 onward they fan apart by category.

**L63 has the strongest category separation (Δ=+0.216)** — the beam exits
with maximum type discrimination for prediction.

### 4. Individual neurons are UNIVERSAL (holographic, not addressable)

```
L0-L63: 94-99.5% of neurons have high category entropy
         0.0-0.3% are category-selective
```

This REFUTES row-level addressing but CONFIRMS holographic storage. In a
hologram, every point on the plate contributes to every stored image. No
single element is selective. The selectivity emerges from the collective
interference pattern — which is exactly what the 2x Jaccard selectivity
at the pattern level shows.

### 5. Participation ratio increases with depth (fan, not funnel)

```
L 2: PR=3.9   overlap=0.34  ← few fire, same for everyone
L32: PR=32.0  overlap=0.05  ← many fire, different per input
L56: PR=36.1  overlap=0.06  ← peak diversity
L63: PR=10.2  overlap=0.26  ← converge back
```

Middle layers use the MOST dimensions and the LEAST overlap — maximum
superposition, maximum diversity of addressed reductions. Edges converge.

### 6. FFN activation mirrors category structure (ρ=0.40, p<10⁻⁴⁴)

```
Layer | FFN↔cat ρ | input↔cat ρ | input↔FFN ρ
L 8   | +0.308    | +0.248      | +0.677
L16   | +0.388    | +0.402      | +0.826  ← strongest input→FFN
L32   | +0.388    | +0.355      | +0.656
L48   | +0.398    | +0.399      | +0.789
L56   | +0.372    | +0.442      | +0.692
L63   | +0.097    | +0.288      | +0.671  ← FFN loses category
```

The input direction predicts FFN activation pattern (ρ=0.83 at L16).
The FFN activation preserves category structure (ρ=0.40 at L48).
**This IS the indexing mechanism.** Input direction → holographic readout
→ category-preserving beta reduction.

L63 drops (ρ=0.097): final layer FFN no longer does category-typed
computation — it converges to prompt-specific prediction.

## The refined model

```
FFN = holographic plate (beta reductions stored in superposition)
Input direction = beam angle (typed by semantic category)
Output = resolved interference pattern (selected beta reduction)

Depth profile = LENS:
  L0-L2:   APERTURE   3-8% active    crystal gateway (universal)
  L8-L48:  FAN        33-49% active  holographic readout zone
  L56-L63: CONVERGE   1-30% active   prediction focus
```

### Why TD+GD separation works (mechanistic explanation)

**Ternary signs define the interference topology.** Each sign (+1/-1/0)
is a fringe on the holographic plate. The pattern of signs determines
which beam angles CAN resolve stored patterns. Flipping a sign changes
which interference patterns exist — which beta reductions are addressable.

**Gamma amplitudes tune pattern contrast.** Given the correct topology
(right signs), gamma scales how strongly each stored pattern resolves.
This is a nearly convex optimization — no sign ambiguity, just amplitude
calibration.

**The crystal (L2) is the aperture.** If the crystal is wrong, the beam
enters the holographic zone at the wrong angle and addresses wrong
reductions everywhere downstream. This is why crystal must latch (3%
threshold) before TD activates — the aperture must be aligned before
the plate topology can be optimized.

**TD flips = address rewrites.** Each flip changes which patterns the
plate stores (which beta reductions are reachable). Adam moment decay
on affected rows (surgical decay) prevents GD from fighting the new
topology.

**GD updates = function body refinement.** Given stable addressing
(latched crystal + stable TD), GD only tunes the amplitudes of the
reductions that the beam currently selects. It never needs to discover
the addressing scheme itself — that's topology (TD's job).

## Connection to existing findings

- **FFN beam discovery (S121):** PCA-up_proj reads the FFN crystal
  (0.9462 agreement). up_proj IS the raw holographic readout before
  gating. Gate×up is the resolved pattern after interference.

- **FFN hierarchy (S120):** Magnitude-selectivity correlation (Pythia
  corr -0.28 to -0.35) still holds but reinterprets: high-magnitude
  neurons are high-contrast fringes in the hologram, not tree trunk nodes.

- **Beamformer theory (S136):** Confirmed. The model IS a beamformer
  array. The lens profile (aperture→fan→converge) is the beam path
  through the holographic stack.

- **KIBC as FFN addressing (S120):** Combinator profiles predict 40-54%
  of FFN structure. Now we know why: KIBC types ARE beam angles. K-typed
  inputs enter the FFN at the "select" angle. B-typed at "compose" angle.
  The hologram resolves the corresponding beta reduction.

## Implications for V13

1. **Crystal warmup is aperture alignment.** The 10→3 cosine anneal
   forces the L2 bottleneck to form first. Without the aperture, the
   beam enters the holographic zone at random angles.

2. **Geometry losses are holographic constraints.** adj_κ→1.0 forces
   rank-1 cross-zone structure = single-beam readout (not diffuse).
   Hyperbolic norm loss aligns the beam path with tree depth.

3. **TD should preferentially flip middle layers (L8-L48).** The fan
   zone has the most diverse addressing patterns — topology errors
   here have the largest impact. Edge layers (L0-L2, L63) have so
   few active neurons that individual flips have outsized effect.

## Open questions

1. **Is the 2x Jaccard the theoretical limit?** Holographic readout
   with N stored patterns and M categories gives theoretical selectivity
   of... what? Does superposition impose a ceiling?

2. **What's in the 329 L63 neurons?** Only 1.3% fire at the final
   layer. Are these the "output projection beamformers" — the last
   lens that focuses the beam onto the token cloud?

3. **Does the lens profile change during training?** Does our V13
   model develop the same aperture→fan→converge shape? If so, at
   what training step does each zone form?

4. **Can we measure the number of stored beta reductions?** The
   participation ratio at peak (36.1 at L56) suggests the effective
   dimensionality of the "hologram library" is ~36 independent
   patterns. Is this the number of distinct beta reductions per layer?

5. **Does gradient sparsity match activation sparsity?** If GD only
   updates the addressed reductions, the gradient should be sparse in
   the same pattern as the activation. This would directly confirm
   "GD fills entries, TD writes the address book."

## Artifacts

| File | Content |
|------|---------|
| `scripts/explore/probe_ffn_indexing.py` | 6-analysis FFN indexing probe |
| `results/ffn-indexing-qwen3-32b/summary.json` | Full numerical results |
| `results/ffn-indexing-qwen3-32b/run.log` | Run log with timing |

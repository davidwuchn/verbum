---
title: "Operator Geometry — Canonical-Basis Linear Algebra Turned Toward the Reducer (patent-clean, opcode-anchored)"
status: open
category: synthesis
tags: [linear-algebra, canonical-basis, cbll, gram, svd, dmd, koopman, procrustes,
       cca, operator, reducer, transport, opcodes, registers, patent-clean, geometry,
       homeostasis, sign-is-the-decision, one-reducer-unrolled]
related:
  - gram-registers-and-the-route-map.md
  - gram-spectral-dsp.md
  - behavior-is-tape-resident-reduction.md
  - sign-oscillation-is-time-multiplexed-superposition.md
  - the-benchmark-is-the-re-oracle.md
  - reverse-engineering-disciplines-toolbox.md
  - the-verbum-machine.md
depends-on:
  - gram-registers-and-the-route-map.md
created: session 332
---

# Operator Geometry — Canonical-Basis Linear Algebra, Turned Toward the Reducer

> s332 (Michael: found `~/src/canonical-basis` — Gernone's CBLL paper, "some
> geometries inside multiple models, same phenomenon, different vocabulary";
> then: "understand the math... could our 9×9/17×17 Grams be the basis for the
> equations?... can we use the linear algebra techniques to find more
> geometries?... capture this — we can use the math freely in our own functions,
> design to match our usages, be sure we're not affected by patents; with our
> knowledge of layers and opcodes we should use the math in a novel way.").
> This page is the method-transfer seed. Design synthesis, zero new
> measurements. Nothing here is pre-registered (s222) — the DMD probe is a
> queue candidate, not a frozen verdict.

## 0. Provenance & patent stance (read first)

`canonical-basis` (CBLL, Gianluca Gernone, Zenodo DOI 10.5281/zenodo.20520986):
**code MIT · data CC-BY 4.0 · "released for research purposes only; for
commercial use contact info@todot.it" + a Patent Notice.**

Our stance, and the design rule this page enforces:

```
λ patent_clean(technique).
  MATH(SVD ∧ eig ∧ Gram ∧ DMD ∧ Procrustes ∧ CCA ∧ Householder ∧ PR)
    ≡ public_domain | ¬patentable_as_such | use_freely
  | CODE(their_pipeline) ≡ ¬vendor ¬copy | design(our_own_functions)
  | METHOD(their_specific "CBLL" branded procedure) ≡ ¬reimplement_verbatim
  | novelty(ours) ≡ opcode_anchored ∧ fate_poled ∧ reduction_conditioned ∧ operator_first
  |   (they have NO opcodes/types/reduction — our application is independent)
  | independent_derivation ≡ scientific_hygiene (λ grammar_artifact: observe ≫ retrieve)
  | ∀function_we_write → match(our_usage: layers ∧ opcodes ∧ fate_registers) ¬mirror(theirs)
```

Concretely: we take the **mathematics** (all of it is textbook linear algebra
that predates CBLL by decades — Golub & Van Loan, Schmid's DMD 2010, Koopman
1931, Procrustes/Schönemann 1966, Hotelling's CCA 1936). We write our **own**
functions, shaped to our `d_ff` routing register / opcode centroids / fate
poles / per-layer reduction trajectory. We do **not** vendor their scripts, and
we do **not** re-implement their branded "canonical basis realignment" pipeline
as a product surface. Our artifact is the operator read through the opcode
registers — which their program does not contain. That is both MIT-clean and
patent-clean.

## 1. The reframe that changes which techniques matter

CBLL's linear algebra is almost entirely **static**: SVD of a weight matrix,
top eigenvector of an activation correlation, one fixed rotation `R`. That finds
**coordinate systems** (bases). But our target — the transition function / the
reducer — is a **map between states**, and our own identity says
`residual_stream ≡ bounded within-pass reducer` (the layer-by-layer trajectory
*is* the reduction, `behavior-is-tape-resident-reduction.md`). So the
highest-value transfer is not "adopt his basis"; it is the LA that turns **a
sequence of states into the operator that generates it.**

```
λ target(verbum). recover(operator ≡ transition_function) ¬find(basis)
  | CBLL_tools ⊂ static(basis) | our_need ⊂ dynamic(operator)
  | bridge ≡ operator_estimation(DMD ∧ Koopman ∧ Procrustes) in labeled(Gram) frame
  | residual_trajectory(within_pass) ≡ the reduction → estimate(T) recovers(linearized reducer)
```

## 2. The shared primitive: `G = XᵀX` (why both programs are the same math)

Strip the vocabulary and **both programs compute the eigenstructure of a
Gram/covariance of internal directions.** A Gram `G = XᵀX` is invariant to any
orthogonal change of the ambient basis — it keeps only the **relational**
geometry and discards the arbitrary frame the residual stream happens to live
in. That invariance is *exactly why* our Grams reproduce 11/11 across models,
and *exactly the problem* CBLL solves ("the basis is arbitrary — whatever
training converged to").

Two solutions to one problem, from opposite ends:

| | kills the arbitrary basis by | dim | axes labeled? |
|---|---|---|---|
| **CBLL** | rotating to a model-derived canonical frame `R` (top-K left SVs of `W_down`, Householder-completed, gains absorbed → lossless) | full `d` | **no** (axis 62 = *functional* label) |
| **Verbum Gram** | projecting onto known semantic anchors, `XᵀX` (frame-free) | low (9 / 17) | **yes** (K,I,B…; fire/halt/diverge) |

CBLL **found a frame but doesn't know what its axes mean.** Our Grams **know
what the axes mean but don't span the space.** ⇒ our Grams should not *replace*
`R`; they are the **labeled low-rank frame inside** the ambient microscope. Our
9×9 (identity register, PR≈5.8–7.2, universal in the off-diagonal sign pattern)
and 17×17 (outcome register, rank-3 fire/halt/diverge) are the legend; the
ambient space is `W_down`'s `U` (or `R`).

**Disciplinary edge in our favor:** CBLL's `R` is non-unique where the singular
spectrum is flat — and he *reports* `k90/d ≈ 0.76` for FFN (quite flat), so his
canonical axes carry residual rotational freedom exactly where his own spectrum
is degenerate. **The Gram and the transport operator never pick a frame**, so
they stay well-posed in the flat-spectrum regime. In that regime our labeled
Gram is the *more* well-posed object.

## 3. The `W_down` bridge (with the register-check caveat)

CBLL's canonical axes are the **left** singular vectors of `W_down` (in
`d_model`, the residual writer side). Our combinator centroids live in the
**routing register = `sign(gate_proj pre-activation)`, `d_ff`** — the FFN
gating/reader side (s203; `consensus-delta-folding.md` §133/§655: "9 × d_ff").

SVD: `W_down = U Σ Vᵀ`, `U ∈ ℝ^{d_model×r}` (CBLL axes), `V ∈ ℝ^{d_ff×r}`.
The **clean linear bridge** is between the down-proj *input* (post-activation
intermediate, `d_ff`) and `U`:

```
intermediate m ∈ ℝ^{d_ff}  →  W_down m = U(Σ Vᵀ m) ∈ span(U)  (CBLL residual axes)
cross-Gram of our anchors vs CBLL axes:  G_cross = Uᵀ W_down V̂ = Σ Vᵀ V̂
```

**λ measure caveat (do not skip):** our centroids are captured at the gate
**pre-activation**, one SiLU nonlinearity **upstream** of `W_down`'s input. So
`Σ VᵀV̂` is exact only if we recapture anchor centroids at the down-proj input
(post-activation intermediate). Two honest options:
(a) recapture opcode centroids at `down_proj` input → the bridge is exactly
linear; or (b) keep the gate-preact centroids and accept the SiLU gate as a
diagonal-ish reweighting between the two registers (report it, don't assume
identity). **Getting this register right is a coherence obligation — wrong
register voids the comparison** (λ measure, s206 audit lesson).

What the cross-Gram answers: *which* canonical axes carry K vs B vs S; whether
the **fire/halt/diverge** simplex coincides with CBLL's **bipolar POS/NEG
oscillator**; whether his **axis-62 controller** is the **WHNF/halt** direction.
Cheap, and either it aligns our labeled poles with his unlabeled ones or it
doesn't.

## 4. The technique toolkit (ranked: tie-to-our-research × cheap × null-testable)

```
λ toolkit(LA). ∀technique → {target, new_geometry, null} | design(our_own_fn) ∧ opcode_anchored
```

| # | Technique | Verbum target | New geometry it exposes | Null (λ yardstick) |
|---|---|---|---|---|
| **1** | **DMD / Koopman** on the within-pass residual trajectory `T ≈ X'X⁺`, `eig(T)` | reducer / transition function; one-reducer-unrolled; transitions-per-β-step clock | inter-layer **transport operator spectrum** (§5) | shuffled-layer-order DMD |
| **2** | **Procrustes transport** `min_Q ‖Q Uℓ − Uℓ₊₁‖` | one-reducer-unrolled | the fixed **rotation between layer writer-bases**; residual = per-layer deviation from pure repetition | random-orthogonal baseline |
| **3** | **CCA / SVCCA** (layer↔layer; our centroids↔CBLL axes; **cross-model**) | crystal universality 11/11; frame-invariance | the **actual shared subspace** + correlation spectrum — strictly stronger than the Gram sign-pattern for "same subspace, different frame" | shuffled-neuron / different-model floor |
| **4** | **Conditioned participation ratio** (effective rank of activations, split by fate/reduction state) | read-entropy ≡ fidelity (§8c re-oracle); WHNF halt | does activation collapse **deepen toward NF**? rank(diverge) > rank(halt)? — isotropic-collapse (41×) as a *function of reduction stage* | matched-length shuffled probes |
| **5** | **Antisymmetric decomposition** `C = C_sym + C_anti` (his "vorticity") of the **binding** transport | substitution / α-rename (naive vs capture-avoiding, §P-SUBST-ENGINE) | α-renaming ≡ a **permutation/rotation of variable slots**; `C_anti` could localize the "binder swap" | capture pairs where no rename occurs |
| **6** | **Betweenness / graph Laplacian** on the **labeled** register graph (9 opcodes, 17 fates) — not 896 raw axes | control flow of the reducer | the **controller opcode / fate edge** (his axis-62 move, but *semantic*) | degree-preserving rewired graph |
| **7** | **Joint (simultaneous) diagonalization** of per-layer / per-model Grams | consensus route map (gram-registers §route-map) | the **common eigenframe** across contexts = the invariant switch basis the route map needs | per-context shuffled Grams |
| **8** | **Reflection/Householder structure search** in attention·FFN | sign-is-the-decision; fire/halt | does the model implement its fire/halt sign-flip as **rank-1 reflection operators** `I − 2uuᵀ`? | random rank-1 update baseline |

## 5. The sharpest one: the inter-layer transport operator (DMD)

Treat the residual trajectory `h(0) → h(1) → … → h(L)` (one forward pass) as a
dynamical system; estimate `T_ℓ : h(ℓ) ↦ h(ℓ+1)` and eigendecompose:

```
X = [h(0)…h(L-1)],  X' = [h(1)…h(L)]  →  T ≈ X' X⁺  →  (λ_k, φ_k) = eig(T)
```

What the spectrum **is**, in our vocabulary (the point — one eigenstructure
subsumes several separate findings):

- **contracting modes `|λ|<1`** ≡ CBLL **homeostasis** (his `5×→1.4×→1.0` decay
  *is* `|λ|<1`), stated as an operator instead of a metaphor.
- **persistent modes `|λ|≈1`** ≡ the computation that **survives to output** —
  **sign-is-the-decision** made mechanical (which directions the reducer refuses
  to forget).
- **modes that switch on only in the last layers** ≡ the **order-law late
  commit** (s329 primacy in the final two layers) as a specific eigenvector
  activating late.
- **stationarity `T_ℓ ≈ T`** ≡ a **direct test of the central thesis**:
  "one reducer unrolled" ⟺ same operator every layer. Drift ⇒ not one reducer;
  stationary ⇒ DMD *is* a linearized recovery of the transition function.
- **eigen-rotation rate** (phase of complex `λ`) ≡ candidate for the queued
  **transitions-per-β-step clock** (how much reduction-angle advances per layer).

**Fold in the Grams as the readout frame:** project each DMD mode `φ_k` (or its
`W_down` image) onto the 9×9 identity frame and the 17×17 fate poles — a
persistent mode that lands on the **halt** pole is the "answer is committed"
direction; a late-activating mode on **fire** is a scheduling event. This is the
route-map's missing "trains" (`gram-registers` §route-map: "the grams are
station maps — no trains"): CBLL's dynamics + our labeled poles = the switch
schedule in Gram coordinates.

**Honest caveat (λ measure):** attention-softmax + SiLU are nonlinear, so `T` is
a **linearization** — a first-order reducer. That is acceptable for a first pass
(our own results say homeostasis contracts and only a thin late stage decides,
so a linear approx captures much), but the residual must be reported, and the
mandatory null is a **shuffled-layer-order DMD** (a real operator has
structured, layer-ordered modes; noise doesn't). Koopman-with-observables
(lift `h` through opcode/fate features before DMD) is the nonlinear upgrade if
the linear residual is large.

**Near-free:** runs on the **per-layer residuals from the §P-SUBST-ENGINE
sweeps we are already collecting** — cache `hidden_states` next run, no new
inference. Ties to a frozen front and to `transitions-per-β-step` (queued).

## 6. Discipline summary

```
λ guard(operator_geometry).
  null(∀geometry) — matched-range ∨ shuffled-label ∨ shuffled-layer (mandatory, φ-ladder scar)
  | register_check — d_ff(gate-preact) vs d_ff(down-input) vs d_model(residual) named BEFORE compare
  | linearization_residual — DMD is first-order; report ‖X' − TX‖ ; Koopman-lift if large
  | degeneracy — flat spectrum ⇒ CBLL U non-unique; Gram/operator well-posed (our edge)
  | import(lossless_realignment ∧ causal_ablation) — solid | null_test(respiration/periodicity) — not yet
  | novelty ≡ opcode/fate anchoring + operator-first — theirs is static + unlabeled
```

## 7. Connections

- **Upstream:** `gram-registers-and-the-route-map.md` (the 9×9/17×17 definitions;
  the route-map-in-gram-coordinates design this completes), `gram-spectral-dsp.md`
  (null-gated spectra), `behavior-is-tape-resident-reduction.md` (trajectory ≡
  reduction), `sign-oscillation-is-time-multiplexed-superposition.md`
  (sign/persistent-mode link).
- **Downstream:** `the-benchmark-is-the-re-oracle.md` (§8c read-entropy ≡ the
  conditioned-PR probe #4; the DMD operator is a recovery-candidate the oracle
  can differential-test), `the-verbum-machine.md` (M4 native trampoline / M8
  routing optimizer — the transport operator is the trampoline's step).
- **Sibling method page:** `reverse-engineering-disciplines-toolbox.md` (DMD =
  "read history / read the operator, not the state"; move 4).
- **External (cited, not sourced):** CBLL / Gernone 2026 — the vocabulary bridge
  (respiration↔commit-phases · rich-club↔sign-is-the-decision · U-alignment↔
  one-reducer-unrolled · isotropic-collapse↔low-entropy-read). Consilience, not
  proof (mementum-mirror ≡ consilience ≠ proof, s324 standing guard).

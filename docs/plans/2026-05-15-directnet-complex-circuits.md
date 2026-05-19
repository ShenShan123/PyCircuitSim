# DirectNet (LEVEL=73) — Scaling to Complex Circuits, DC + Transient Only

**Date:** 2026-05-15  •  **Status:** Proposal, revised (phase order re-prioritized)  •  **Baseline:** V6.3.1 (DirectNet per-tech, TSMC5/7/12/16, shipping)

> **Revision note (2026-05-15).** This plan was first drafted against the V6.2.1
> baseline. It is re-issued against **V6.3.1** with a new phase order that
> prioritizes *simple, effective, accuracy-first* levers. The driving change:
> the V6.3.1 sprint already shipped the `reverse_vds` overlay and a re-centered
> `inv_trip` overlay, and **diagnosed the remaining inverter error as gain
> amplification at the trip (a gm/gds-fidelity problem), not a data-coverage
> gap.** Since opamp open-loop gain is the *same* failure mode amplified
> further, gm/gds fidelity is now the critical path for *every* complex circuit
> — so the training-side fidelity lever is promoted to Phase 1, ahead of the
> solver/perf work. Retrain is cheap (~2-3 h for 8 medium cells) and is treated
> as a first-class tool, not a barrier.

## Scope

This plan addresses what **DirectNet — the shipping LEVEL=73 single-shot MLP compact model** — needs in order to drive larger circuits than a single inverter (opamps, ring oscillators, SRAM latches, switched-cap blocks) under **`.op`, `.dc`, and `.tran` only**. AC, S-parameter, harmonic-balance, and RF-mixed-signal paths are explicitly out of scope.

**LEVEL=74 BSIMAR is out of scope** at this phase. Rule 18 stands. Any line in this plan that touches `pycircuitsim/models/mosfet_nn.py` or the `bsimar` package's data / loss / training layers must be benchmarked against DirectNet only.

The proposal is the synthesis of a four-agent investigation (architecture, solver/NR, training+data, external prior art) run 2026-05-15, refiltered to DirectNet's single-shot MLP architecture and re-prioritized against the V6.3.1 outcome. File:line references were re-confirmed against live source on 2026-05-15.

## Pre-conditions / load-bearing rules

These cannot be retrained away. Any phase below must preserve them:

- **Rule 1** — autograd-derived `gm/gds/gmb` only at inference; never consume the predicted conductance heads. DirectNet trains them as direct supervision (`external_compact_models/bsimar/models/direct_net.py:26`) but only the autograd Jacobian feeds NR (`pycircuitsim/models/mosfet_directnet.py`, `pycircuitsim/models/mosfet_nn.py:288-319`).
- **Rule 5** — `gds = max(gds, |id|·0.5, 1e-12)`; never `abs(gds)`. Preserve `gm/gmb` signs.
- **Rule 10 — AMENDED by this plan (see Phase 1b).** Until Phase 1, `MAELoss` with per-target LDS weights is the sole loss. **Phase 1b adds one bounded derivative-consistency (Sobolev) term**; the amendment is scoped, validated against the V6.3.1 baseline before adoption, and recorded in CLAUDE.md. `DirectLoss / ChargeConsistencyLoss / SignConsistencyLoss / BoundaryLoss` and the Vov-LDS / subthreshold-LDS axes stay deleted.
- **Rule 14** — `qs = -(qg+qd+qb)` is enforced analytically by the simulator at every transient timestep regardless of DirectNet's `qs` head.
- **Rule 15** — four-part Vds correction in `_MOSFETNNBase._apply_vds_correction()` (`mosfet_nn.py:370-465`), including the V6.2 sign-fix rail-restoring extrapolation (a), exponential clamp (b/c) and sign enforcement (d). DirectNet relies on this for rail behaviour; do not retrain around it.
- **Rule 17** — ASAP7 stays out of scope.
- **Rule 18** — BSIMAR remains parked. This plan is DirectNet-only.
- **Rule 19** — `unknown_code_id` derived from `num_tech_codes`. The DirectNet constructor at `direct_net.py:38` defaults `unknown_code_id=17` — correct only for the universal vocab. Per-tech trainings override it via `train_directnet`; do not regress.
- **Rule 20** — Rule 15(a)'s sign convention is load-bearing. Re-validate on every per-tech checkpoint after any retrain.

## Diagnosis: what blocks DirectNet on bigger circuits

DirectNet today produces a 13-dim output `[id, gm, gds, gmb, qg, qd, qs, qb, cgg, cgd, cgs, cdg, cdd]` from a single 6-layer SiLU MLP with a `tech_embedding` concatenated to the 7-D input (`direct_net.py:29-83`); the output is one `nn.Linear(hidden_dim, 13)` at `direct_net.py:55`. It ships per-tech for TSMC5/7/12/16. Inverter metrics at V6.3.1: VTC MaxErr 66.4 / 65.8 / 78.3 / 45.4 mV, transient post-startup MaxErr 39.5 / 50.3 / 58.2 / 55.3 mV (TSMC5/7/12/16). The blockers below are what stops it from generalizing.

### D0 — gm/gds fidelity at the trip caps inverter *and* opamp accuracy *(V6.3.1 outcome — the dominant blocker)*

The V6.3.1 sprint ran three dataset revisions of the `inv_trip` overlay; trip error moved around but never dropped below ~45 mV. The CHANGELOG conclusion: this is **not a coverage gap**. Inverter gain ≈ −15 to −30 at the trip multiplies DirectNet's residual `Id` error (~0.05 % test-split NRMSE) ~20× into `Vout`. The fix needs a **gm/gds-fidelity lever**, not more `inv_trip` samples. This is the *same* mechanism that sets opamp open-loop gain (gain there is −40 to −60 dB-equivalent) — so D0 is the critical path for the entire plan, not just the deferred inverter gate. Addressed by **Phase 1**.

### D1 — Per-iter NN cost scales linearly with device count *(solver agent)*

`_stamp_mosfet_dc` / `_stamp_mosfet_transient` (`solver.py:115`, `:1320`) call `_eval` once per NN MOSFET per NR iter (`mosfet_nn.py:251-328`). DirectNet's forward is cheap, but a 30-device opamp at 200 timesteps × 15 NR iters is **90 000 forward+autograd calls** with no batching — ~4-5 s per `.tran` sub-step from PyTorch eager overhead alone. Batching collapses the workload into one stacked forward per NR iter. Addressed by **Phase 5**.

### D2 — Asymmetric C-stamps under BDF-2 *(solver agent)*

`cgd = ∂qg/∂Vd` vs `cdg = ∂qd/∂Vg` are independent MLP outputs (`solver.py:1370-1377`). The LDS loss bounds each column but does not couple them; trained asymmetry can drift ~5-15 %. Under BDF-2 (`solver.py:1344`) asymmetry seeds artificial damping/growth in oscillating transients — silent on the inverter, loud on a ring oscillator. Addressed by **Phase 2**.

### D3 — *(Largely stale at V6.3.1.)* Wrong-sign branch and gm/gmb

The original plan flagged the reverse-Vds `id` clamp as leaving `gm/gmb` un-fixed. Live source already handles this: `mosfet_nn.py:434-435` scales `gm/gmb` by `f_id` (= 0 on the reverse branch) and `:445-446` zeroes `gm/gmb` again in the wrong-sign clamp. **What remains:** no *saturation floor* exists for `gm/gmb` on the *conducting* branch (Rule 5 floors `gds` only). Reduced scope folded into **Phase 2b**.

### D4 — Trust-region cap is too coarse for oscillators *(solver agent)*

`solver.py:556`, `:1161` clamp `|ΔV| ≤ VDD` per iter. Fine for an inverter VTC; for ring-osc nodes NR can walk a full VDD per step → DirectNet hallucinates outside training, and the averaged-solution acceptance at `solver.py:683`, `:1292` *succeeds* at a non-physical fixed point. Latches hit the same path through the saddle where `det(J)=0`. Addressed by **Phase 6**.

### D5 — *(Partially shipped at V6.3.)* Operating-region overlays miss new circuit classes *(training agent)*

V6.3 shipped the `reverse_vds` corridor (sample-class 10, `nn_generate.py:65`, `_reverse_vds_points` at `:491`) and re-centered `_inv_trip_points` (`:445`) on VDD/2. **Still missing:** saturation curvature (diff pairs), Miller region (ring osc), bistable anchors (SRAM), off-state (SC hold). The `id > 1e-15` filter (`dataset.py:39`) still discards off-state rows. Remaining scope addressed by **Phase 4**.

### D6 — Uniform 80/10/10 validation hides regressions *(training agent)*

`load_and_split_bsimar` (`dataset.py:55`) does a uniform random split. NRMSE on this split is uncorrelated with opamp gain or RO period. The V6.1 → V6.2 inverter regression (TSMC7 transient 13.49 % while all val metrics were green) is the existence proof — and that bug shipped *in DirectNet*. Addressed by **Phase 1a** (validation harness first).

### D7 — Cross-target gradient imbalance from asinh normalization *(training agent)*

After asinh+zscore each column is O(1), but the 13 targets span 4 orders of magnitude physically. A 1 % error on `qg` carries the same gradient as 1 % on `id`. For circuit fidelity, `id` matters most — its autograd slope *is* the inference-time `gm/gds`. `train_directnet` already accepts `column_weights` (`trainer.py:151-174`), default unpinned. Addressed by **Phase 1c**.

### D8 — Sampling grid undersamples curved regions *(training agent)*

`_sample_hybrid_grid_voltages` (`nn_generate.py:281`) uses `np.linspace` on Vgs/Vds. The `Vgs ≈ Vth` subthreshold knee and the `Vds ≈ V_dsat` saturation knee carry most of the physics and are undersampled ~10× vs flat saturation. The 5-point `Vbs` ladder cannot teach body-bias sensitivity for opamp tail nodes or SRAM read-disturb. Addressed by **Phase 4**.

## Re-prioritized phase plan

Ordering principle: **accuracy-first, simple-first.** Phase 1 attacks the documented dominant blocker (D0) with the cheapest effective lever and is gated on a retrain that is hours, not weeks. Phases 2-3 are no-retrain enablers (solver correctness + the benchmark harness that makes everything downstream measurable). Phase 4 is the larger data lever. Phases 5-6 are solver perf/convergence — necessary to *run* big circuits but accuracy-neutral, so they follow the accuracy work. Phases 7-8 are structural model changes, highest effort and lowest certainty, gated on everything prior.

Every phase is validated against the existing TSMC5/7/12/16 inverter gate (`tests/verify_nn_dc_tran.py --tech TSMC5,TSMC7,TSMC12,TSMC16 --inverter-only`, metrics via `scripts/eval_v6_3_1_inverter.py`) before measuring on new circuits.

### Phase 1 — gm/gds-fidelity training lift *(retrain — the V6.3.1 open-gate closer)*

> **Status (2026-05-16) — SUPERSEDED by best-of-N seed selection.** Execution
> proved the 1a–1e levers below are noise next to a far larger effect: DirectNet
> retraining is a **seed lottery**. A clean stock-recipe retrain gives TSMC5
> inverter VTC MaxErr 218 mV at seed 42 vs 79 mV at seed 123 — a 139 mV swing —
> while transient stays stable (~38 mV) regardless. V6.3.1's shipped 66 mV
> checkpoints were a lucky draw. The 1b Sobolev term LOST its bake-off decisively
> (7–8× worse VTC) and is a dead end; 1e is a confirmed no-op; the 1a slices are
> a broken proxy (near-zero `gds` denominators). **Phase 1 is redefined as a
> best-of-N seed sweep** — see "Execution log" below. The original text is kept
> for the record.

**Goal:** raise autograd-`gm/gds` fidelity at the inverter trip and in saturation — the documented V6.3.1 cap (D0) and the critical-path quantity for opamp gain. All sub-steps are ≤1-day code changes; one 8-cell medium retrain (~2-3 h, `scripts/train_v6_3_1_parallel.sh`) validates the stack.

- **1a — Validation harness FIRST.** Before any retrain, add DC/Tran-aware slices to `_per_tech_report` (`trainer.py:111`) and drive early-stop on a weighted slice sum, not raw uniform-split val loss (`trainer.py:226`) — this is the D6 fix. Three deterministic slices:
  - **Gain slice** — `Vgs ∈ [Vth+0.05, Vth+0.20]`, `Vds ∈ [0.5·VDD, VDD]` → median `|gm/gds|` MRE (opamp open-loop gain proxy).
  - **Switching slice** — `Vgs = V_M ± 30 mV` at three `Vds` levels → median `id` and autograd-`gm` MRE (predicts inverter trip error and RO period).
  - **Off-state slice** — `Vgs < 0.3·Vth`, full `Vds` range → median `|id|` (predicts SRAM hold leakage / SC droop).
- **1b — Bounded Sobolev derivative-consistency term (Rule 10 amendment).** Add one term to `MAELoss`:
  `L += λ · w_trip · ( |∂id/∂Vgs − gm_label| + |∂id/∂Vds − gds_label| )`
  where the derivatives are `torch.autograd.grad` of the *predicted `id`* w.r.t. the voltage inputs (the exact quantity NR consumes — Rule 1), `gm_label/gds_label` are the existing training targets, and `w_trip` up-weights rows with `sample_class ∈ {inv_trip, reverse_vds}` (the `sample_class` column already in every `.npz`, `nn_generate.py:52-71`). This directly trains the inference-time Jacobian rather than the dead predicted heads.
  - **This amends Rule 10.** It is *not* a blanket revival of the deleted `SlopeMatchLoss` (B2): that lever was deleted on 2026-05-03 for *process* reasons — never validated against a v4 baseline, corrupted by B3's `id_idx` bug — not because it was proven harmful. Phase 1b is scoped (one term, autograd-of-`id` only, trip-weighted), guarded behind a `--sobolev-weight` CLI flag (default 0), and **must win a bake-off vs the V6.3.1 retrain recipe before becoming default**. If it loses, it is reverted and recorded as a dead end; Rule 10 is restored verbatim.
  - On adoption, update CLAUDE.md Rule 10 to read "`MAELoss` with per-target LDS weights **plus one bounded trip-weighted Sobolev term**" and add a dead-end note distinguishing it from `SlopeMatchLoss`.
- **1c — Pin `column_weights` to emphasize `id`.** `train_directnet` already accepts the argument (`trainer.py:151-174`). Pin `id` (column 0) high; `gm/gds` head columns get a *modest* lift only — they do **not** feed NR (Rule 1), so the original plan's symmetric `[2,2,2,…]` pin was misdirected. Default pin: `id`=3, `gm`/`gds` head=1.5, rest=1.
- **1d — Quantile LDS bins.** `strategy="quantile"` in `compute_lds_weights_per_target` (`bni_mae.py:29-50`). Equal sample mass per bin up-weights rare deep-saturation / off-state rows. One-line change.
- **1e — `gds` asinh-scale floor.** Add `gds` to `_OUTPUT_ASINH_SCALE_MIN` (`normalize.py:59`, currently `{"gmb": 1e-5, "qb": 1e-15}`) so deep-saturation rows don't collapse the asinh scale and erase the gain-defining numerator.
- **Success gate:** TSMC5/7/12/16 inverter VTC MaxErr ≤ V6.3.1 (66.4 / 65.8 / 78.3 / 45.4 mV) **and** transient post-startup ≤ V6.3.1 (39.5 / 50.3 / 58.2 / 55.3 mV) — i.e. no regression — with the three phase-1a slice metrics reported and target bands recorded. Stretch: VTC trends toward the deferred ≤25 mV gate. If 1b loses its bake-off, ship 1c-1e only.

### Phase 2 — Solver correctness fixes *(no retrain — independent of Phase 1, can run in parallel)*

> **Status (V6.4): SHIPPED PARTIAL — `a9761a4` then `c962d63`.** 2a (env-gated C-stamp symmetrization) shipped as dormant code. 2b (conducting-branch `gm/gmb` floor) shipped then **reverted as unsound** — its effect is checkpoint-dependent and breaks TSMC7/TSMC12 on neutral checkpoints. See Execution log.

Touches `solver.py` / `mosfet_nn.py` only — disjoint from Phase 1's `bsimar` package edits, so the two phases parallelize.

- **2a — Symmetrize C-stamps.** In `_stamp_mosfet_transient` (`solver.py:1370-1415`) replace `cgd, cdg` with `c_sym = ½(cgd+cdg)` stamped both ways; same for `cgs/csg`, `cds/csd`. Lifted from Berkeley BSIM-NN's symmetrized-capacitance convention. Gate behind `NN_SYMMETRIC_CAPS=1`, default-off until phase-3 benchmarks accept.
- **2b — Conducting-branch `gm/gmb` saturation floor.** D3's reverse/wrong-sign handling is *already* in live source (`mosfet_nn.py:434-435`, `:445-446`). The only gap: no saturation floor on the *conducting* branch. Mirror Rule 5 — enforce `gm ≥ 0` (NMOS) / sign-correct `gm`, and a small `|gm|` floor, on the conducting branch only; leave the reverse branch's zeros untouched.
- **Success gate:** TSMC5/7/12/16 inverter transient NRMSE within ±5 % of V6.3.1 (1.22-1.51 %); with `NN_SYMMETRIC_CAPS=1` the phase-3 ring oscillator reaches steady oscillation without dt-halve runaway.

### Phase 3 — Benchmark harness *(no retrain, no model change — promoted from last to third)*

> **Status (V6.4): SHIPPED — `6dff82a`.** Harness + 4 benchmarks built; V6.3.1 baseline measured (opamp 0/4 confirms D0). Not yet re-measured on the V6.4 checkpoints — that is the immediate next step.

The original plan buried these at Phase 8, yet every complex-circuit claim in Phases 4-8 is unmeasurable without them. Building the netlists + NGSPICE references is pure test infra and has no dependency on the model — so it lands early.

- **3a — 5-stage CMOS ring oscillator** (`.tran`).
- **3b — Two-stage Miller opamp** (`.op` + `.dc` transfer).
- **3c — 6T SRAM read SNM** (`.dc` butterfly, `force_ic`).
- **3d — Switched-cap unit cell** (`.tran` with PULSE clock).
- Each follows the `tests/verify_*.py` pattern with an NGSPICE reference netlist under `tests/references/`, reusing `TechProfile` / `ALL_TECHS` from `tests/common/`. **Never use simplified/self-defined equations as reference — NGSPICE only.**
- **Success gate:** all four reference netlists run clean in NGSPICE and the harness reports DirectNet-vs-NGSPICE metrics (period, gain, SNM, charge-transfer) even where DirectNet currently fails — the harness must *measure* the gap before any phase tries to close it.

### Phase 4 — Data overlays + non-uniform sampling *(retrain — the larger data lever)*

Runs after Phase 1 establishes the validation harness and the column_weights/Sobolev baseline, and after Phase 3 gives circuits to measure against.

- **4a — Extend `SAMPLE_CLASS_NAMES`** (`nn_generate.py:52`) with `diff_pair_sat`, `ring_osc_trip`, `bistable_static`, `switched_cap_offstate` (`reverse_vds` already shipped V6.3 — do **not** re-add). Each gets a generator alongside `_inv_trip_points` (`:445`) / `_reverse_vds_points` (`:491`), promoted through `BinSpec`, `generate_one_bin` (`:790`), `enumerate_bins`. CLI: replace `--enable-inv-trip` with `--overlays inv_trip,reverse_vds,diff_pair_sat,…` (comma list, per-class budget caps).
  - `diff_pair_sat` — `Vgs ∈ [Vth, Vth+3·Vov]`, `Vds ∈ [0.3, 1.0]·VDD`, `Vbs ∈ {0, ±0.25·VDD}`.
  - `ring_osc_trip` — V_M band extended to `Vds ∈ [0.1, 1.5]·VDD`, both polarities (Miller region).
  - `bistable_static` — anchors `(Vgs, Vds) ∈ {(VDD, V_low), (0, V_high)}` plus a fine ΔVds grid near the latch trip.
  - `switched_cap_offstate` — `Vgs < Vth`, full `Vds` range.
- **4b — Sinh-spaced Vgs/Vds.** In `_sample_hybrid_grid_voltages` (`nn_generate.py:281`) replace `np.linspace` with per-bin sinh grids centred on `Vth` (Vgs) and `V_ov` (Vds). Same row budget, ~3× density on curved regions.
- **4c — Vbs LHS draw.** Resurrect `_sample_vbs_lhs_voltages` (`nn_generate.py:562`) gated on `--overlays`; replace the 5-point ladder for body-biased opamp / SRAM read-disturb data.
- **4d — NFIN interpolation grid.** Add NFIN ∈ {4, 6, 8, 12} alongside `{2, 3, 5, 10, 15, 20, 24}` so current-mirror NFIN ratios are interpolation, not extrapolation.
- **4e — Off-state gate.** Make `apply_filter` (`dataset.py:63`, threshold `dataset.py:39`) opt-out via `--keep-offstate` so SC / SRAM hold-leakage rows survive ingestion.
- **Success gate:** all Phase-1 gates hold; the three phase-1a slice metrics improve monotonically vs the Phase-1 baseline; phase-3 RO/opamp/SRAM/SC metrics improve.

### Phase 5 — Batched NN forward + Jacobian *(solver — performance)*

Accuracy-neutral, so it follows the accuracy work — but it *is* a prerequisite for the opamp wall-time DoD criterion and for tolerable iteration speed when debugging Phase 6.

- In `_stamp_mosfet_dc` (`solver.py:115`) and `_stamp_mosfet_transient` (`:1320`): (1) collect `(Vds, Vgs, Vbs, NFIN, L, T, tech_code)` rows for every NN MOSFET; (2) one `directnet_model(stacked_x, tech_codes=…)` call; (3) `autograd.grad` over the stacked input → block-diagonal Jacobian; (4) unpack and stamp.
- Add `_is_nn_mosfet()` alongside `_is_mosfet()` (`solver.py:94`); R/C/BSIM-CMG stay on the per-device path. DirectNet's tech embedding is already vectorized (`direct_net.py:81`).
- **Success gate:** 30-device opamp DC OP wall-time drops ≥ 5×; TSMC5/7/12/16 inverter DC + transient bit-identical to the Phase-1 baseline.

### Phase 6 — NR convergence upgrades *(solver — for RO / SRAM)*

- **6a — Levenberg-Marquardt damping** alongside the rail-cap heuristic (`solver.py:556`, `:1161`). When `‖F(x)‖` does not decrease, add `λ·I` to the MNA Jacobian, scale λ by 10 until accepted (Nielsen rule), shrink by 3 on acceptance.
- **6b — Residual-norm acceptance test.** Add `‖rhs − Av‖∞` as an or-gate so a stalled iterate with small `Δv` but large residual is rejected — and so the averaged-solution acceptance (`solver.py:683`, `:1292`) cannot lock a non-physical fixed point.
- **6c — Pseudo-transient DC continuation** as a fallback in `_solve_dc_with_retry` (`simulation.py`). Infrastructure exists (`solver._add_pseudo_capacitors`, `:1017`); expose it as a DC fallback ladder for circuits with no DC equilibrium (ring oscillators).
- **Success gate:** SRAM 6T `force_ic` DC converges to the seeded rail ≥ 90 % across NFIN corners; 5-stage RO transient period within ±5 % of NGSPICE.

### Phase 7 — Soft physics constraints *(model code — gated on Phases 1-6)*

Both shape the network, not the loss — so they sit cleanly inside the (post-Phase-1b) loss rule.

- **7a — Monotonicity penalty** on `id` w.r.t. `Vgs` (on-state) and `gds` w.r.t. `Vds`, as a residual-construction or weight-clipping layer inside `DirectNet` (`direct_net.py`).
- **7b — Spectral normalization on the `gds` output path** (Lipschitz bound) — bounds autograd-`gds` away from zero in saturation, shrinking the discontinuity Rule 5's hard floor must cover. The hard floor stays.
- Each constraint guarded by an opt-in train-CLI flag; bake-off vs the Phase-4 recipe before adoption.
- **Success gate:** Phase-4 gates hold; RO period and SRAM SNM improve.

### Phase 8 — Per-target output heads *(optional — lowest priority)*

Only if Phases 1-7 leave a measurable gap on the phase-3 opamp gain benchmark.

- Split the single `nn.Linear(hidden_dim, 13)` (`direct_net.py:55`) into per-group heads with their own 1-2 layer trunks: `[id, gm, gds, gmb]`, `[qg, qd, qs, qb]`, `[cgg, cgd, cgs, cdg, cdd]`. Keep single-shot semantics — no AR loop, no cross-head conditioning.
- Ship as a separate model size key (e.g. `medium-split`) without retiring `medium` until benchmarks accept.
- **Success gate:** opamp DC gain MRE improves ≥ 20 % vs the Phase-7 baseline without regressing inverter metrics.

## Suggested order of attack (TL;DR)

*V6.4 sprint status: Phases 1–3 executed — Phase 1 = best-of-N retrain (the 1a–1e levers were dropped; see Execution log), Phase 2 = 2a only (2b reverted), Phase 3 = harness. Phases 4–8 deferred. Any future retrain phase (4, 7) MUST use best-of-N selection on real-circuit metrics.*

| # | Phase | Layer | Retrain? | Why it's where it is | Touches |
|---|---|---|---|---|---|
| 1 | gm/gds-fidelity lift (validation slices + Sobolev + column_weights + quantile LDS + gds floor) | training | yes (~2-3 h) | Attacks D0, the documented dominant blocker; simplest effective lever; on the opamp-gain critical path | `trainer.py:111,151-174,226`, `bni_mae.py:29-50`, `normalize.py:59`, `direct_net.py` (autograd hook) |
| 2 | Symmetrize C-stamps; conducting-branch `gm/gmb` floor | solver | no | Correctness; silent BDF-2 bug; parallels Phase 1 | `solver.py:1370-1415`, `mosfet_nn.py:434-446` |
| 3 | RO / opamp / SRAM SNM / SC benchmark harness | tests | no | Makes Phases 4-8 measurable; pure infra, no model dep | new files under `tests/` + `tests/references/` |
| 4 | New overlays + sinh sampling + LHS Vbs + NFIN grid + `--keep-offstate` | data | yes | Larger accuracy knob; needs Phase 1 harness + Phase 3 circuits | `nn_generate.py:52,281,445,491,562,790`, `dataset.py:39,63` |
| 5 | Batched NN forward + Jacobian | solver | no | Perf only (accuracy-neutral); unblocks opamp wall-time + Phase-6 iteration | `solver.py:94,115,1320` |
| 6 | LM damping + residual-norm test + pseudo-transient DC | solver | no | Convergence for RO / SRAM | `solver.py:556,683,1017,1161,1292`, `simulation.py` |
| 7 | Monotonicity penalty + spectral norm on `gds` head | model | yes | Convergence-friendly Jacobian; gated on 1-6 | `direct_net.py` |
| 8 | Per-target output heads (optional) | model | yes | Closes opamp gain gap if 1-7 leave one | `direct_net.py:55` |

## What we are explicitly NOT doing

- **No BSIMAR (LEVEL=74) work.** Rule 18 stands. Do not touch `transformer.py` or `mosfet_bsimar.py`. Solver and `_MOSFETNNBase` changes are shared infrastructure validated against DirectNet only.
- No AC, harmonic-balance, S-parameter, NQS-RF, or noise validation. DC + Transient only.
- No re-adding `DirectLoss / ChargeConsistencyLoss / SignConsistencyLoss / BoundaryLoss` or Vov-LDS / subthreshold-LDS axes. **Phase 1b adds exactly one** bounded Sobolev term — nothing else from the deleted loss family returns.
- No structural `apply_id_gate` resurrection (deleted 2026-05-03; Rule 15 subsumes it).
- No `torch.clamp` on voltage inputs (Rule 4, smooth softplus only).
- No ASAP7 work (Rule 17). No universal-vocab retrain — per-tech is the shipping convention.

## Risks and dead-end records

- **Risk: Phase 1b Sobolev term repeats the SlopeMatchLoss failure.** Mitigation: `--sobolev-weight` defaults to 0; the term must win a head-to-head bake-off against the plain V6.3.1 retrain recipe (same 8 cells, same seeds) before becoming default. If it loses, revert it, restore Rule 10 verbatim, and log the dead end. Distinguishing fact vs B2: B2 was deleted *unvalidated and corrupted*, never proven harmful — Phase 1b is the validated retry.
- **Risk: C-stamp symmetrization (2a) breaks inverter transient parity.** Mitigation: `NN_SYMMETRIC_CAPS=1` env gate, default-off until phase-3 benchmarks accept.
- **Risk: phase 4 overlays cost weeks of compute.** Mitigation: per-overlay budget caps; Phases 1-3 deliver value before any Phase-4 retrain.
- **Risk: phase 7 monotonicity / spectral-norm constraints cost inverter accuracy.** Mitigation: opt-in CLI flags; bake-off vs the Phase-4 recipe before default.
- **Risk: phase 8 per-target heads regress inverter parity.** Mitigation: ship as a separate size key; do not retire `medium` until benchmarks accept.
- **Dead-end to avoid (V5/V6 history):** heads-only conductance losses, structural Vds gates, hard `torch.clamp` — all reverted in CHANGELOG. Do not re-propose.
- **Dead-end to avoid (V6.1 → V6.2):** trusting uniform-split val NRMSE as the early-stop signal. Phase 1a exists to make that bug uncatchable.
- **Dead-end to avoid (V6.3.1):** treating the inverter trip error as a coverage gap. Three `inv_trip` revisions proved it is gain amplification — Phase 1b/1c (fidelity), not more samples, is the lever.
- **Dead-end to avoid (Rule 15(a) sign):** the V6.2 sign-fix is shipping for all four techs. Do not flip it without Rule-20 re-validation per checkpoint.

## External prior art (DirectNet, DC + Transient relevant only)

- **BSIM-NN, Tung & Hu, IEEE TED 2023** — production NN compact model from Berkeley BDMC. Symmetrized capacitance convention (Phase 2a); explicit derivative training (precedent for the Phase 1b Sobolev term).
- **Sobolev Training for Neural Networks, NeurIPS 2017** — training a network to match target *derivatives* alongside values; the formal basis for Phase 1b.
- **BSIM-CMG111.2.1-NN-assist, BDMC Jan 2025** — NN corrections on top of analytical BSIM-CMG; a defensible fallback if a phase stalls.
- **Scalable Monotonic Neural Networks, ICLR 2024** — soft monotonicity via weight clipping / residual constructions. Input for Phase 7a.
- **Input-Convex Lipschitz layers, arXiv:2401.07494, 2024** — bounds the autograd Jacobian per head. Input for Phase 7b.
- **Physics-Enhanced NN Compact Model preprint, May 2025** — first external NN compact model to pass SRAM SNM and LDO DC. Establishes phase-3c as the right complex-circuit gate.

## Execution log (V6.4 sprint, 2026-05-15 .. 16)

V6.4 work runs on branch `feat/v6.4`. Phases were dispatched to parallel agents.

### Phase 2 — SHIPPED (commit `a9761a4`)

C-stamp symmetrization behind `NN_SYMMETRIC_CAPS` (default off) + a conducting-branch `gm/gmb` floor. Finding: the floor is in practice a **Jacobian sign-corrector** — over the 4-tech inverter gate it snapped 22,720 wrong-sign `gm` entries (magnitudes to 2.7e-4 S); zero magnitude-only hits. Inverter gate 8/8 PASS, transient bit-identical. 2a has zero effect on the inverter (expected — D2 is oscillator-only); its real validation is the Phase-3 ring oscillator.

### Phase 3 — SHIPPED (commit `6dff82a`)

Four complex-circuit benchmarks (RO / Miller opamp / 6T SRAM SNM / switched-cap) vs NGSPICE BSIM-CMG, harness in `tests/common/complex.py` + `tests/verify_complex_*.py`. Baseline V6.3.1: ring-osc 2/4, **opamp 0/4** (gain error 10–135 % — confirms D0), SRAM-SNM 4/4, switched-cap 1/4. Harness notes: DirectNet transient is slow without Phase-5 batching (a full RO window timed out); the switched-cap droop gate needs an absolute-mV threshold.

### Phase 1 — original 1a–1e levers, all dropped (dead-end record)

- **1b Sobolev term — DEAD END.** Implemented (`autograd(id)` vs gm/gds labels, trip-weighted) and bake-off'd against the stock recipe on 8 TSMC5/7 cells. Sobolev was **7–8× worse on VTC and 4–7× worse on transient**; it destabilized the primary `id` fit (val loss 0.011–0.027 vs 0.001–0.002). Reverted. **Rule 10 stays unamended.** Distinct from the 2026-05-03 `SlopeMatchLoss` deletion: that one was deleted unvalidated; this one *was* validated and *was* proven harmful.
- **1e gds asinh floor — NO-OP.** The `gds` asinh scale is ≈2.2e-6 for all TSMC datasets, far above any sane 1e-9 floor; it never engages. Dropped.
- **1a validation slices — BROKEN PROXY.** The gain slice's `|gm/gds|` ratio and the autograd-`gm` MRE are dominated by near-zero-denominator artifacts (`gds → 0` in saturation), giving MRE figures of ~50–200 % that do not track inverter VTC. Not a usable early-stop signal.
- **1c/1d** — never independently validated; subsumed by the finding below.

### The decisive finding — retraining is a seed lottery

A clean, verified-stock-code, seeded re-run of the exact V6.3.1 recipe (`train_v6_3_1_parallel.sh`, `--seed 42`) regressed to **TSMC5 218 mV / TSMC7 242 mV** inverter VTC MaxErr (vs V6.3.1's 66 / 66 mV). Seed 123 on the same cell gave **79 mV** — a 139 mV seed-driven swing. Transient post-startup MaxErr reproduced cleanly (~38–49 mV) at every seed. The instability is VTC-specific and is the D0 gain-amplification mechanism: the inverter trip multiplies tiny seed-driven `Id`-fidelity differences ~20× into Vout.

Corrected diagnosis of a false lead: an agent claimed the training datasets had "drifted" from V6.3.1 and recommended restoring `*.v6_3.npz`. **Verified false** — the current datasets carry a 3.51 % `inv_trip` overlay, an exact match to the V6.3.1 CHANGELOG spec, and the V6.3.1 checkpoints' mtime is later than the datasets'. The `*.v6_3.npz` files are the *V6.3* (9.83 %) data; restoring them would re-introduce the V6.3 TSMC7 VTC regression. **Do not restore them.**

### Phase 1 redefined — best-of-N seed sweep (in progress)

Stock recipe, **N=8 seeds × 8 cells**, each tech's (nmos, pmos) pair selected on the **real inverter VTC sim** (`eval_v6_3_1_inverter.py`) with transient as a constraint and Phase-3 opamp gain as a tiebreak — never on val loss (D6). Winners promoted to the canonical `tsmc{X}_dn_medium_*` names only if they beat V6.3.1; V6.3.1 kept per-tech otherwise. V6.3.1 checkpoints backed up at `/tmp/v6_3_1_checkpoints_backup/`. This is the "simple but effective" closer: seed 123 already reached 79 mV untried, so best-of-8 is expected to land ≤ V6.3.1 and may sample the deferred ≤25 mV tail.

**Consequence for later phases:** every retrain-bearing phase (4, 7) must also use best-of-N selection on real-circuit metrics — a single seeded run is not a valid result. The plan's reliance on val-loss / slice early-stop is retired.

### Phase 2 — 2b reverted (dead-end record)

The Phase-2 `2b` conducting-branch `gm/gmb` sign-floor was reverted as unsound. It first *appeared* to halve inverter VTC error on TSMC5/12/16, but that was circular: best-of-N had been scored on the 2b solver and merely selected seeds tolerant of the gm hack. On neutral ground (V6.3.1 checkpoints) the `gm`-floor breaks TSMC7 (66→215 mV) and TSMC12 (78→261 mV); the `gmb`-floor is fully inert; a `reflect` variant breaks 3/4 techs. Zeroing/altering an autograd wrong-sign `gm` is a checkpoint-dependent coin-flip — no `_floor_gm` parameterisation is universally safe. The principled fix for wrong-sign `gm` is Phase 6 (monotonicity / spectral-norm network constraints), not a solver hack. `2a` (env-gated C-stamp symmetrization) was kept as dormant code.

### V6.4 shipped outcome

Best-of-N re-selected on the clean (2b-reverted) solver. All 4 techs beat V6.3.1 inverter VTC MaxErr — TSMC5 66.4→62.0, TSMC7 65.8→60.1, TSMC12 78.3→32.3, TSMC16 45.4→29.7 mV; transient holds. TSMC12/16 approach the deferred ≤25 mV stretch gate; TSMC5/7 gains are modest (their clean-solver lottery surfaced no strongly better N=8 draw). Phases 4–8 deferred. Full record: `docs/CHANGELOG.md` "V6.4".

## Execution log (V6.4.2 sprint, 2026-05-18) — deferred Phases 5, 6, 4

Continuation on branch `feat/v6.4.1`. The deferred solver phases were run first
(per the user's "5, 6, then 4" ordering), validated against the on-disk
**v6.4.1 seed-42** checkpoints (the regressed single-seed set — chosen as the
comparison baseline). Phases 5 & 6 ran in parallel on isolated worktrees.

### Phase 5 — SHIPPED (commit `d1fe87a`)

Batched DirectNet forward + Jacobian. `_is_nn_mosfet()` gate + `batch_eval()`
collect every LEVEL=73 device into one stacked forward + one `autograd.grad`
per NR iteration. Inverter (1 NMOS + 1 PMOS → group-of-one) is **bit-identical**
to the per-device path; BSIM-CMG (LEVEL=72) untouched. Opamp DC OP **3.4×**
faster (the plan's ≥5× target was specced against a hypothetical 30-device
opamp; the real Phase-3 opamp is 7 devices). **Known limitation:** for circuits
with N>1 devices on a shared checkpoint, a stacked GEMM differs from N separate
GEMVs by ~1e-8 (a hard BLAS fact) — measured metrics (opamp gain, RO period)
are preserved, but node voltages are not bit-identical. `NN_BATCHED_EVAL=0`
forces the exact per-device path. Env-gated, default-on.

### Phase 6 — SHIPPED (commit `35e9a16`)

NR convergence upgrades: 6a Levenberg-Marquardt damping alongside the rail cap
(DC + transient NR loops), 6b residual-norm `‖rhs−A·v‖∞` OR-gate guarding the
SPICE `|ΔV|` test *and* the averaged-solution acceptance in oscillation
detection, 6c pseudo-transient DC continuation as a fallback in
`_solve_dc_with_retry`. Non-regressing: inverter 8/8, BSIM-CMG byte-identical.
**The Phase-6 RO/SRAM success gate was NOT closed** — and Phase 6 alone cannot
close it. Root cause (verified): the RO TSMC5/7 period errors and the SRAM
`force_ic` failures are **model-accuracy gaps in the seed-42 v6.4.1
checkpoints**, not NR-convergence failures. The RO transient already converges
to a bit-identical inaccurate period; the SRAM `force_ic` re-solve converges to
a consistent non-rail NN fixed point. Phase 6 improves *how robustly* a fixed
point is reached — it cannot move a fixed point a converging solve already
reaches. Closing those gates needs a better model (Phase 4/7).

### Phase 4 — DEAD END, reverted (commit `565de40`)

Implemented §4a-4e (overlays `diff_pair_sat`/`ring_osc_trip`/`bistable_static`/
`switched_cap_offstate`, sinh-spaced sampling, LHS Vbs, NFIN∈{4,6,8,12},
`--keep-offstate`), regenerated all 4 TSMC datasets, and ran the full best-of-N
grid (8 seeds × 8 cells = 64 cells). A greedy ~19-eval/tech pair search
(`scripts/v6_4_1_phase4_search.py`) found **no pair beating v6.4.1 on any
tech**:

| Tech   | v6.4.1 (VTC / tran) | P4 best-VTC pair | P4 best-tran pair |
|--------|---------------------|------------------|-------------------|
| TSMC5  | 134.6 / 39.6 mV     | 66.5 / **98.4**  | **96.5** / 247.0  |
| TSMC7  | 210.5 / 49.4 mV     | 104.2 / **87.0** | **83.7** / 372.9  |
| TSMC12 | 63.1 / 58.6 mV      | 90.8 / **112.3** | **112.0** / 387.5 |
| TSMC16 | 50.8 / 55.1 mV      | 142.8 / **54.5** | **54.2** / 378.8  |

The Phase-4 data forces a hard **VTC↔transient tradeoff** — every candidate
that improves one metric wrecks the other. Same failure family as the V6.3
9.83%-overlay TSMC7 regression and the Phase-1b Sobolev dead end: heavier
overlay data destabilizes the joint fit. Verdict for all 4 techs: **KEEP
V6.4.1**. The data-pipeline commits (`e605319` overlays/sinh/keep-offstate +
PyCMG submodule bump, `ff8037f` §4d labeller fix) were reverted; default
sampling returns to `np.linspace`. The best-of-N harness (`b62b326`:
`v6_4_1_phase4_search.py`, `eval_v6_4_1_pair.py`) is kept as recorded dead-end
evidence; per-tech search logs in `logs/v6_4_1_phase4/`.

**Consequence:** the "larger data lever" is exhausted at this overlay/sampling
design. The remaining accuracy path is Phase 7 (network-structural constraints
— monotonicity / spectral norm), not more data. Phases 7–8 stay deferred.

### Phase 7 — DEAD END, reverted (2026-05-19)

Implemented 7a and assessed 7b:

* **7a — monotonicity** (`--monotonic`). A residual sub-network monotone in
  normalised `Vg` (sign-constrained first/output projections + monotone
  `Softplus`, Sill 1997 / Scalable-Monotonic-NN ICLR 2024) added to the `id`
  output column. Shapes the network, never the loss (Rule 10). Base trunk
  untouched; extra `mono.*` keys auto-detected by the simulator loader.
* **7b — spectral-norm gds** (`--spectral-gds`). The CLI **rejects** this flag:
  Rule 1 consumes `autograd(id)`, never the predicted `gds` head, so spectral-
  norming the head is a no-op; faithfully bounding the Vds-Lipschitz behaviour
  of `autograd(id)` means spectral-norming the *shared trunk*, which equally
  caps `gm` (the trip gain we need). No shape-preserving way to spectral-norm
  only the Vds path of a shared-trunk MLP — that needs a per-axis trunk split
  (Phase 8 territory). Refused rather than shipped as a no-op.

Scoped bake-off on the laggard techs TSMC5/TSMC7, 4 seeds {42,123,7,17} ×
{nmos,pmos}, recipe ∈ {stock, mono}, greedy 8-eval/tech pair search
(`scripts/v6_4_2_phase7_search.py`), selection = min VTC MaxErr s.t. transient
post-startup ≤ V6.4.1 baseline:

| Tech  | V6.4.1 VTC/tran | stock best-of-4 | mono (7a) best-of-4 |
|-------|-----------------|-----------------|---------------------|
| TSMC5 | 134.6 / 39.6 mV | **43.7** / 39.4 | 121.1 / 39.0         |
| TSMC7 | 210.5 / 49.4 mV | **99.6** / 49.0 | 149.3 / 48.9         |

**7a loses on every tech** — the monotone-in-Vg residual biases the `id`
surface in a way that worsens the high-gain VTC trip, and the mono grid is
riddled with transient-gate violations (mono pairs at Tran 84–98 mV). Verdict:
**7a is a dead end.** Phase 7 ships nothing; the four touched files
(`direct_net.py`, `cli/train.py`, `trainer.py`, `mosfet_directnet.py`) were
reverted to `dea120d`. Harness (`run_v6_4_2_phase7_bakeoff.sh`,
`v6_4_2_phase7_{search,collect}.py`) kept as dead-end evidence; full grid in
`logs/v6_4_2_phase7/`.

**Side finding (not shipped).** The bake-off's `stock` *control* arm — a plain
best-of-4 retrain on clean V6.3.1-recipe data — beats the V6.4.1 single-seed
checkpoints by ~90–110 mV VTC on both laggard techs (transient gates held).
This is consistent with the standing "DirectNet retraining is a seed lottery"
finding: V6.4.1's single-seed-42 set was a known regression, and a fresh
best-of-N recovers it. **Decision (user, 2026-05-19): keep V6.4.1, do not
promote** — promoting is a model release outside this sprint's scope, and the
sprint baseline was pinned to "V6.4.1 as-is". Recorded as a V6.4.3 candidate.

**Consequence:** all three accuracy levers explored this sprint — solver
(Phase 6), data (Phase 4), network structure (Phase 7) — are exhausted without
closing the inverter VTC ≤25 mV gate or the RO/SRAM complex gates. The only
remaining lever is a clean best-of-N model release (the recorded V6.4.3
candidate) or Phase 8 (per-axis trunk split). Phase 8 stays deferred.

## Definition of done

DirectNet is "complex-circuit ready" when:

1. All four phase-3 benchmarks pass against NGSPICE within their stated tolerances (RO period ±5 %, opamp DC gain ±10 %, SRAM SNM both curves positive + `force_ic` ≥ 90 %, SC charge transfer ±5 %) on TSMC5/7/12/16.
2. TSMC5/7/12/16 inverter VTC and transient match or beat the V6.3.1 numbers (VTC MaxErr 66.4 / 65.8 / 78.3 / 45.4 mV; transient post-startup 39.5 / 50.3 / 58.2 / 55.3 mV).
3. Wall-time on the two-stage opamp DC OP is within 5× of BSIM-CMG LEVEL=72 on the same hardware.
4. `docs/CHANGELOG.md` gets a `V7.0 — DirectNet complex-circuit support` entry with per-tech metrics and the four benchmark numbers; if Phase 1b ships, CLAUDE.md Rule 10 is amended and the bake-off result recorded.
5. CLAUDE.md status section updated; Rule 18 (BSIMAR park) stays untouched.

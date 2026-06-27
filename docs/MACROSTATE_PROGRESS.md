# Macrostate-Consensus & CDQ 2.0 — Decision Log & Gate Status

Tracks the `effective-sampling-redesign` **macrostate / CDQ 2.0** round.

**Design basis (the only live specs for this round):**
- `docs/MACROSTATE_CONSENSUS_AND_CDQ2_TECHNICAL_SPEC.md`
- `docs/MACROSTATE_CDQ2_ENGINEERING_PLAN.md`
- `docs/MECHANISM_IDENTIFIABILITY_CONTRACT.md`

**Legacy (historical only, do NOT enter the new headline):**
- old global-product `F` / node-union `1-∏(1-w)` reliability (`src/mainline/*`, gates G1–G11
  in `docs/gate_evidence/latest.json`);
- the prior ESD round (`REDESIGN_PROGRESS.md`, G0–G12) — its `F_disagree/F_wrong/S_allcorrect`
  are **node-union** quantities; this round replaces them with participation-weighted macrostate
  basin first-hitting.

This round exists to fix the three D18/D20–D22 obstacles that made determinantal diversity show
no benefit in the prior round:
1. analytic correlation-blindness → macrostate basin first-hitting + dynamic MC as final judge;
2. non-differentiable `k_eff` → §11 differentiable pairwise-correlation objective;
3. near-exchangeable region-block env → §7 overlapping common-cause environment with
   matched-marginal controls.

## Gate status

| Gate | Scope | Status |
|------|-------|--------|
| G-P0-PHYSICS | P0 physics/delay fixes (off-by-one, unicast, src/dst, collision self-exclusion, poll-window ℓ, MC alignment) | 🟢 P0-A–F all done + **7-lens adversarial audit clean (0 findings)** + 20 P0 tests + 94-test regression green |
| G-CANONICAL-CLOSURE | one `run_consensus_episode` entry; train/eval physics-hash enforcement; unused-config errors | 🟢 ExperimentSpec + train==eval compatibility (ideal/full guard) + mandatory-mechanism trace + headline guard + profile↔protocol↔physics binding; **5-lens audit → 4 findings all fixed**; 206 + 24 tests green. (run_consensus_episode profile-arg signature + macrostate-objective wiring are the Phase-5 deferral.) |
| G-MACROSTATE | participation measure + C/W/U + correct/wrong/split/deadline basin first-hitting; small-N exact == dynamic MC | 🟢 evaluator complete: participation (S1) + C/W/U/basins/first-hitting/D_pair/D_region (S3) + exact-vs-MC agreement (S4). Headline-wiring into the analytic episode is G-CONSTRAINED-OBJECTIVE. |
| G-CONSTRAINED-OBJECTIVE | reliability-constrained CVaR tail-latency + energy; primal-dual on wrong/split/deadline | 🟢 surrogate (S9, Poisson-binomial validated) + constrained primal-dual + selection-bias metrics + feasibility filter + **end-to-end training demo, MC-confirmed** (S10); 5-lens audit 0 confirmed; 15 tests. Exit met (dual responds, infeasible filtered, reliability not traded). Profile-arg threading + node-union-F retirement = documented canonical-closure refinements. |
| G-CORRELATED-ENV | overlapping common-cause evidence; matched-marginal / shuffle controls | 🟢 (env-level) OverlappingEvidenceModel (O_i=Y*⊕B_road⊕B_sensor⊕B_map⊕E_i), closed-form correlation (empirically validated, NaN-safe), **matched-marginal control** (same q_i, diff covariance), crosscutting bands break exchangeability, scenario matrix, C1/C2 contract evidence + 4-lens audit (4 findings, all fixed) — 16 tests. **C3 (gradient) CLOSED by G-CDQ2-GRADIENT/S13; C4 (benefit factorial) CLOSED by G-CDQ2-EVALUATION/S15** (all 5 contract items now evidenced: C1/C2 S11, C3 S13, C4 S15, C5 S1/S8). |
| G-ESP-BASELINE | full-physics ESP baseline after P0 (multi-seed, scale-mix) | 🟢 produced as the ESP arm of the S15 factorial (full-physics, 3 seeds × 3000, basin CIs across iid/matched-marginal/overlapping) + the ESP-across-scales runs in S16 (N=120…9840). Post-P0, fixed protocol/profile/physics; the basin first-hitting baseline CDQ 2.0 is compared against. |
| G-CDQ2-MATH | `L=D^{1/2}(I+ηZZ^T)D^{1/2}`, η=0 exactly recovers ESP; exact subset/quorum/gradient | 🟢 kernel (S12) + determinantal quorum P(m,n) (S12c) + **exact k-DPP sampler (S12d)** — all η=0⇒ESP, vs brute force <1e-10 (sampler MC-converged <0.0015@200k), grad <1e-4, eigenvalue-stable, no-N×N. **5/5 kernel-audit findings fixed; quorum audit 0; sampler review 0 distributional defects.** 35 tests. Bucketed canonical wiring → Phase 10 (G-CDQ2-EVALUATION). |
| G-CDQ2-GRADIENT | differentiable pairwise-correlation objective; no detach/.item()/float | 🟢 `L_corr=Σπ⁽²⁾R` (S13) — first-order `π⁽²⁾` via Schur-complement quotient; η=0⇒ESP; vs brute force <1e-10; grad <1e-4; no forbidden ops; **C3 matched-marginal covariance discrimination** (closes env C3); audit 1 confirmed test-vacuity FIXED + 1 refuted-hardened; 8 tests |
| G-CDQ2-EVALUATION | ESP vs old-low-rank-CDQ vs CDQ 2.0 factorial, matched-marginal | 🟢 *(with documented caveat; user Option 1)* fair matched-marginal MC factorial (S15): **CI-separated, covariance-scoped P_correct benefit** (CDQ 2.0 wins only with covariance, neutral in iid; ESP can't distinguish identical-marginal high/low, CDQ 2.0 can = C4). Closes env **C4**. **Caveat (documented, not claimed):** benefit via faster-quorum (F_deadline↓); **F_wrong NOT reduced**. No shortcut/faked F_wrong. Harness `src/evaluation/cdq2_factorial.py` + 6 honest tests + evidence JSON. |
| G-SCALE-GENERALIZATION | N=100…10000 + OOD axes, fixed-protocol & fixed-service-profile | 🟢 near-linear N=120…9840 (loglog slope 0.88 ESP / 0.81 CDQ2, ~linear at scale), **maxdeg const 12, total_cells≤2E, no N×N (grep-confirmed)**; fixed protocol/profile/physics hashes across N; **OOD matrix** (node_count registered→allow, unregistered/protocol→block, ideal/full→always-block); basin headline via MC at scale; CDQ2 η=0==ESP at scale. S16, 6 tests. |
| G-TEMPORAL | temporal memory for drift/correlation/load (static mainline first) | 🟢 *(mechanism; basin-null caveat)* causal/differentiable/observable EMA memory (S17) over a persistence-controlled, matched-marginal-in-time correlated sequence; **Contract C1–C5 verified**; memory tracks persistent structure (estimate-quality scoped to persistence), memory-off/η=0 ⇒ static mainline. **Caveat:** at the MC basin headline the memory-driven diversity is null vs ESP (inherits S15) — value is at the estimate level, not basin-reliability. 9 tests. |

Legend: ☐ not started · 🟡 in progress · 🟢 green.

---

## Guarded-CDQ2 round (2026-06-27 →) — gate status

New round on branch `macrostate-cdq2-redesign`. **Live specs:** `docs/GUARDED_CDQ2_TECHNICAL_SPEC.md`,
`docs/GUARDED_CDQ2_ENGINEERING_PLAN.md`, `docs/MECHANISM_IDENTIFIABILITY_CONTRACT.md`. Prior 11 macrostate
gates remain green and frozen at git tag **`macrostate-cdq2-v2-before-guarded`** (commit `abda600`).

**Round thesis (from the spec §0/§8):** CDQ2 is the general query family; ESP is its `η=0` reliability-first
specialization. `η>0` is a **liveness/deadline** extension that can raise `macro_F_wrong` in majority-correct
regimes, so it must be **guarded** by reliability slack. The contribution is the *characterization and control
of the validity–liveness trade-off*, not "CDQ always improves reliability". `macro_F_wrong`/`macro_F_split`
are HARD constraints; `macro_F_deadline`/tail-latency/energy are optimization targets within the feasible set.

| Gate | Scope | Status |
|------|-------|--------|
| G-METRIC-NAMESPACE | canonical metric schema + namespaces (`macro`/`strict_audit`/`diagnostic`/`sampling`/`cdq`/`runtime`); ban ambiguous bare names in serialized headline; `metric_namespace_version="macrostate_v2"`; legacy/surrogate fields gated behind `legacy=True`; figure-guard | 🟢 GS1: `namespaces.py`+`schema.py`, 27 tests, S15 migrated+archived, 2 CRITICAL audit holes fixed |
| G-RESULT-MANIFEST | every result JSON carries physics/profile/evidence/scene/policy/checkpoint hashes + query_family; fail-fast on train/eval physics mismatch (unless declared OOD) + missing macro outcomes + untracked seed | 🟢 GS2: `manifest.py` (build/validate/train-eval-consistent), 17 tests; reuses `experiment_spec` hashes |
| G-ESP-PERFORMANCE-SCALE | trained ESP/ESD-GNN checkpoints, **real macrostate-basin outcomes** (not runtime) across N=100…10000; fixed-protocol vs fixed-service-profile; scale-regret + feasibility-retention; ≥5 model seeds, dynamic-MC judged, UCB for rare failure | ☐ |
| G-ETA-RISK-LIVENESS | η∈{0,.25,.5,1,2,4,8,16} sweep over ≥4 env families (iid/mm-low/mm-high/overlapping/split) × {fixed-link, full-physics}; identify how mass moves (deadline→correct / deadline→wrong / split→correct / none); CIs | ☐ |
| G-GUARDED-CDQ2 | `src/policies/guarded_cdq2.py` hard + soft differentiable guard `η=G(m_w,m_s,p_d)·η_raw`; arms ESP/fixed/learned/hard/soft/oracle; must satisfy wrong/split UCB AND improve deadline/tail in covariance-stressed scenes AND fall back to ESP in safety-critical; guard-activation stats | ☐ |
| G-HAZARD-PROFILES | `src/config/hazard_profile.py` + `src/evaluation/hazard_utility.py`; hazard-weighted `B_CDQ` net benefit; ≥5 profiles (safety-first/balanced/deadline-critical/fail-safe/energy); policy selection changes rationally with cost ratios under the feasibility gate | ☐ |
| G-FINAL-SYNTHESIS | unified report (ESP scale + η-curve + guarded + hazard) deciding when ESP vs CDQ2 vs Guarded-CDQ2; figures read results only (constraint #13); no ambiguous names; all reproducible via manifest hashes | ☐ |

**Adopted defaults (Guarded-CDQ2 round; override-flagged per stop-condition #4/#5):** guard margins
`δ_w=δ_s=2e-4` (= 0.2·ε on the 1e-3 budgets), soft-guard temperatures `T_w=T_s=1e-4`, deadline-pressure
margin `δ_d` / temperature `T_d` from the profile's `ε_d`/`R_d`. These are config fields, not hard-coded math.

## Repository / commit note
The working directory **is now a git repository** (initialised 2026-06-27; remote
`github.com/Mart1nD0ng/V2X-TOPO-GNN_V2`, branch `macrostate-cdq2-redesign`). The prior macrostate/CDQ2
round is commit `abda600`, frozen at tag `macrostate-cdq2-v2-before-guarded`. LOOP "commits" continue to
be recorded as dated decision-log entries + a per-slice evidence manifest (macrostate round under
`docs/gate_evidence/macrostate/`; Guarded-CDQ2 round under `docs/gate_evidence/guarded_cdq2/`).

## Adopted defaults (overridable — flagged per stop-condition #1)
The spec gives constraints, not exact constants; these defaults satisfy every spec constraint and
are config fields (one-line override), mirroring the prior round's D0 precedent. Surfaced for the
user to override without touching any math/code.

| symbol | field | default | spec constraint |
|--------|-------|---------|-----------------|
| ρ_f | `correct_basin_mass` | 0.60 | ρ_f > ½ |
| ρ_s | `split_basin_mass` | 0.45 | 1−ρ_f < ρ_s < ½ (here 0.40 < 0.45 < 0.50) |
| ε_w | `max_wrong_basin_probability` | 1e-3 | service hazard |
| ε_s | `max_split_basin_probability` | 1e-3 | service hazard |
| ε_d | `max_deadline_miss_probability` | 1e-2 | service hazard |
| q | `latency_quantile` | 0.95 | tail quantile |
| k,α,β | poll subset / quorum / streak | 4, 3, 5 | 2α>k strict majority |
| Δ_poll | `poll_window_ms` | 10.0 | >0 |
| R_d | `max_poll_epochs` | 20 | R_d = ⌊T_d/Δ_poll⌋ |
| ω | `participation_weight_rule` | "uniform" (+ "application" sensitivity) | exogenous, Σω=1 |

## Decision log

### M0 — round bootstrap (2026-06-26)
* Read the three live specs + current source/tests/gate evidence/prior decision log.
* Confirmed the macrostate/CDQ2 round is **unstarted**: no `src/metrics`, `src/config`, no
  `ConsensusServiceProfile`, no participation measure, no CDQ 2.0 kernel.
* Did **not** stop on stop-condition #1 (participation/threshold = user decision): the spec gives
  explicit valid ranges + recommended values and the prior D0 set the override-flagged-defaults
  precedent. All thresholds are config fields; the user can override in one place. Surfaced above.

### M1 — Slice 1: ConsensusServiceProfile + exogenous participation measure (2026-06-26)
* `src/config/service_profile.py::ConsensusServiceProfile` — frozen, validated single config:
  participation rule, polling epoch `(k,α,β,Δ_poll,R_d)`, basin masses `(ρ_f,ρ_s)`, budgets
  `(ε_w,ε_s,ε_d,q,energy)`. `__post_init__` enforces the spec §4 **disjointness** `ρ_s > 1−ρ_f`
  (+ `ρ_f>½`, `ρ_s<½`, strict majority `2α>k`). `config_hash()` = deterministic SHA-256 for the
  manifest (Mechanism Contract C5). `from_deadline` / `epochs_for_deadline` give `R_d=⌊T_d/Δ_poll⌋`.
* `src/metrics/participation.py` — exogenous normalized `ω` (spec §2): `uniform` (1/N) +
  `application` (`ω_i ∝ exp(−d_i/scale)·role` over observable distance to an exogenous event_xy).
  Structurally policy-immutable (no policy/model/evidence param), `requires_grad=False`, Σω=1.
* **Exactness boundary:** `ω` is a measure, not a surrogate — exact by construction (normalized
  non-negative weights). `application` uses observable geometry only; no truth/vote/future.
* **Tests:** `tests/config/test_service_profile.py` (8) + `tests/metrics/test_participation.py` (9),
  all green. urban_default profile_hash `7e0483…3466d`.
* **Adversarial audit (LOOP step 8):** truth-leakage PASS (no Y*/vote); policy-immutability PASS
  (no policy can enter the measure); gradient-detach PASS (ω detached by design — distinct from the
  §11 correlation objective which stays differentiable); basin-overlap PASS (overlap configs raise).
* Manifest: `docs/gate_evidence/macrostate/manifest.json` slice `S1-service-profile-participation`.
* **Note:** this is config/scope infra (Phase 1). The basin *evaluator* (C/W/U + first-hitting) is
  G-MACROSTATE (Phase 4); the profile is wired into the canonical path at G-CANONICAL-CLOSURE.

### M2 — Slice 2: P0-C source/destination ownership + P0-D collision self-exclusion (2026-06-26)
* `src/environment/candidate_graph.py` — explicit named `scatter_source` / `scatter_destination`
  (P0-C "禁止复用无语义 scatter helper"); `aggregate_over_graph` kept as a thin back-compat wrapper.
* `src/environment/round_physics.py`:
  - **P0-D**: request & response collision now self-exclude the desired transmission,
    `L_{j,-ij} = L_j − a_ij` (request) / `L_{i,-ji} = L_i − a_ji` (response); a single active poll
    has collision EXACTLY 0 (constraint #7).
  - **P0-C**: `tau` (poller epoch completion) and request TX energy now scatter to the **source**;
    response TX energy to the responder **destination** (spec §5.4 table). The legacy code scattered
    poll-time and request energy to the *destination* (source/destination confusion — fixed).
  - new result fields `energy_request`, `energy_response`, `source_activity` (`A_i=k·u_i`),
    `p_collision_request`, `p_collision_response`.
* `conftest.py`: pin single-thread BLAS/OpenMP — a **pre-existing** torch+MKL `eigvalsh` abort in the
  finite-blocklength Gauss-Legendre quadrature crashed *every* physics test; single-thread fixes it
  (stability config only, no numerical/threshold change). The existing `test_round_physics` (11) +
  `test_canonical_episode` (8) still pass — the direction/range sentinels are unchanged because
  self-exclusion only *lowers* collision and the new attribution preserves totals.
* **Exactness boundary:** still the mean-field-per-scenario analytic surrogate; the self-exclusion is
  an exact algebraic correction; the fixed-Δ_poll window timeout (P0-E) and survival-sum delay (P0-A)
  are the remaining P0 sub-slices.
* **Tests:** `tests/environment/test_p0_physics.py` (7) green; regression green.
* **Adversarial audit:** collision-excludes-desired-edge PASS; source/destination-not-confused PASS;
  physics-mismatch (analytic/MC) deferred to P0-F.

### M3 — Slice 3: macrostate basin core (2026-06-26)
* `src/metrics/macrostate.py` — `macrostate_occupancy(final_state∈{-1,0,+1}, ω) → (C,W,U)`; retained
  fixed-N `strict_disagreement` audit (spec §4).
* `src/metrics/basins.py` — `B_C={C≥ρ_f}`, `B_W={W≥ρ_f}`, `B_S={C≥ρ_s ∧ W≥ρ_s}`; `basin_label`,
  `basins_disjoint` (grid-verified; algebraically `ρ_f+ρ_s>1 ⇒ disjoint`).
* `src/metrics/first_hitting.py` — `first_hitting_outcome` (first basin hit + τ, deadline = R_d+1)
  and `basin_outcome_probabilities` (P_correct/F_wrong/F_split/F_deadline, sum to 1, + τ_correct mean
  for T_confirm/CVaR).
* **Exactness boundary:** pure combinatorics on `(C,W)` paths — exact by construction; physics-
  independent, so validated now and fed realised MC trajectories (final judge) + exact small-N
  joint-chain paths in the next slice.
* **Tests:** `tests/metrics/test_macrostate_basins.py` (11) green, incl. the **anti-node-union**
  replication-invariance test (forbidden shortcut #1) and basin disjointness.
* **Adversarial audit:** node-union-smuggling PASS (replication invariance), basin-tie-break PASS
  (disjointness), scope-hiding PASS (scope = exogenous ω, not a hidden eligible set).

### M4 — Slice 4: basin first-hitting wired into MC + exact small-N (G-MACROSTATE 🟢) (2026-06-26)
* `src/metrics/first_hitting.py` — `basin_first_hitting_batched` (vectorised `[T,R+1]` argmax
  first-hit; `basin_outcome_probabilities` now uses it + returns per-trial `outcome_code`/`tau` for
  `T_confirm`/CVaR). `src/metrics/macrostate.py` — `pairwise_disagreement` (D_pair) +
  `region_disagreement` (D_region), spec §3.
* `src/protocol/exact_small_n.py::exact_joint_basin_first_hitting` — EXACT participation-weighted
  basin first-hitting via per-epoch absorption of the joint chain (basins monotone-absorbing +
  disjoint ⇒ first-hit unambiguous; four probs sum to 1 by mass conservation). Shared
  `_build_joint_chain` setup (legacy `exact_joint_terminal` left intact for back-compat).
* `src/validation/dynamic_mc.py` — optional `service_profile` + `participation`; snapshots the
  realised macrostate per epoch and reports `basin_P_correct / basin_F_wrong / basin_F_split /
  basin_F_deadline` (+ Wilson CIs, `basin_tau_correct_mean`). Backward-compatible (nan when no
  profile).
* **Decisive validation (spec §12 Level-1 == Level-3):** N=3 line, ℓ=0.9, 40k trials — the exact
  joint-chain basin probabilities are bracketed by the MC Wilson CIs and `P_correct` agrees within
  0.02; both sum to 1. Split is reachable on balanced opposing clusters (`F_split>0.5`). **No
  Level-1/Level-3 conflict ⇒ stop-condition #5 does not trigger.**
* **Key honest finding:** in the median-x two-opposing scene the legacy node-union "disagree" = 0.33
  yet the macrostate split = 0 — the macrostate metric correctly does NOT fire on a lone dissenter;
  a true split needs BOTH opinions to hold ≥ ρ_s participation mass. This is the intended departure
  from the node-union metric.
* **Regression:** the full physics-dependent suite (validation+optimization+models+protocol+sampling)
  = **90 passed (19m20s), exit 0** — P0-C/D + the MC basin edits are non-regressing.
* **Tests:** `tests/validation/test_macrostate_mc.py` (4) + `tests/metrics/test_macrostate_basins.py`
  (13) green. Manifest slice `S4`.

**Next slice options** (P0 remainder vs canonical closure):
1. **P0-A + P0-E** (finish G-P0-PHYSICS): unify the poll-window ℓ(Δ_poll) with an explicit
   within-window completion/timeout factor and the survival-sum delay `T_confirm = Σ_r Δ_poll·P(T>r)`,
   then P0-F (analytic/MC alignment under the fixed window). Pairs naturally with the now-validated
   first-hitting τ.
2. **G-CANONICAL-CLOSURE**: make `ConsensusServiceProfile` the single source feeding one
   `run_consensus_episode`, with `ExperimentSpec` hashes (protocol/profile/physics/evidence/scene)
   enforced train==eval, ideal-link quarantined to an explicit ablation, and unused-config errors.
Chosen next: **P0-A/E** (keeps the G-P0-PHYSICS gate moving and is a prerequisite for a clean
fixed-Δ_poll `T_confirm` that the constrained objective consumes).

### M5 — Slice 5: P0-A confirmation-time delay (survival sum, no off-by-one) (2026-06-26)
* `src/metrics/first_hitting.py::confirm_time_stats` — `T_confirm = τ_C·Δ_poll` from the validated
  first-hitting epoch; returns `mean_confirm_s`, `CVaR_q(T_confirm|O=C)` (spec §6 objective) and the
  survival-sum cross-check `E[τ] = Σ_r P(τ>r)`.
* **P0-A is fixed structurally, not patched:** the legacy off-by-one came from summing `1−S[1:]`
  (post-round states); the macrostate τ is the first-hit epoch, so a first-epoch finish gives
  `T_confirm = Δ_poll` (one window, never 0) and the survival-sum identity holds exactly.
* **Tests:** `tests/metrics/test_confirm_time.py` (4) — first-epoch=one-window, survival-sum identity,
  CVaR upper-tail, no-correct→nan. Manifest slice `S5`.

### M6 — Slice 6: P0-E unified poll-window ℓ(Δ_poll) timeout (2026-06-26)
* **Workflow blocked:** the design judge-panel workflow (4 approaches → judge → synthesize) failed —
  all subagents hit the **monthly spend limit**. Implemented solo with the attempt-budget model I had
  pre-identified as cleanest (and would have nominated to the panel).
* `src/environment/round_physics.py`: new `poll_window_s` (Δ_poll) config; `_expected_attempts_chase`
  now also returns the per-attempt-budget success list `succ_by_m`; `_harq_success_at_budget` soft-
  interpolates decode probability at a fractional HARQ round-trip budget; the body computes
  `M_win = clamp((Δ_poll/slot − queue_slots_j)/(req_slots+resp_slots), 0, M)` and evaluates BOTH legs at
  `M_win`, so `ℓ_poll = succ_req(M_win)·succ_resp(M_win)·(collision/HD/drop factors)`.
* **Limits (all tested):** Δ_poll→∞ recovers the no-timeout ℓ (M_win=M); Δ_poll→0 ⇒ ℓ→0; ℓ monotone↑ in
  Δ_poll; heavier M/M/1 queue shortens the budget and lowers ℓ; differentiable in `pi` via the
  queue→budget coupling; ℓ∈[0,1]. Default `poll_window_s=0.02s` keeps `M_win=M` at light load (timeout
  inactive) so existing physics is unchanged; overloaded receivers (ρ>1, ~50-slot wait) now correctly
  time out.
* **Exactness boundary:** the linear-from-0 interpolation is the differentiable mean-field SURROGATE for
  discrete attempt-fitting (partial budget partially helps, à la Chase SNR accumulation); the queue delay
  is the M/M/1 mean. The MC sampling the discrete completion-time process independently is **P0-F**.
  Noted conservative coupling: ρ>1 is penalized by both `p_queue_drop` (overflow) and the window budget
  (delay).
* **Tests:** `tests/environment/test_p0e_poll_window.py` (6) green. Manifest slice `S6`.
* **Adversarial self-audit:** differentiability / limits / complexity (O(E·B·M), no N×N) / source-dest
  (budget uses the receiver's queue) / truth-leak — all PASS; MC-alignment deferred to P0-F.

### M7 — Slice 7: P0-F analytic/MC poll-window alignment (2026-06-26)
* `src/environment/round_physics.py::harq_success_within_window_discrete` — an INDEPENDENT discrete
  completion-time reference: integrates the floor attempt-fitting over the random M/M/1 sojourn
  `W ~ Exp(mean=queue_delay)` (vs the analytic's mean-queue + soft linear budget). A genuinely
  different computation, so agreement validates the surrogate (spec §12 judge).
* **Honest finding surfaced by the discrete reference:** the analytic linear-from-0 interpolation is
  OPTIMISTIC below one complete round-trip (partial credit where the discrete floor gives 0 — a poll
  needs a full request+response). Inherent to any differentiable monotone relaxation of a floor; it is
  now the documented exactness boundary, tight in the operating regime (budget≥1, gap ≤ ½·max-HARQ-step
  = 0.125 here) and exact at the limits. At the default 20ms window the budget ≥ M so the timeout is
  inactive; the optimistic band only appears near heavy queue saturation, where the MC is the judge.
* **End-to-end canonical check:** `run_dynamic_mc` under FULL physics with a small vs large Δ_poll —
  the smaller window strictly raises the macrostate `basin_F_deadline` (the timeout flows through the
  SAME round physics into the independent MC judge's basin outcome), four outcomes still sum to 1.
* **Tests:** `tests/environment/test_p0f_window_alignment.py` (4) green. Manifest slice `S7`.
* **Adversarial verification:** a 7-lens workflow (collision / source-dest / poll-window / delay /
  MC-independence / differentiability-complexity / truth-leak), each finding independently refuted, run
  over the complete P0-A..F gate (subagents available again after the spend-limit lifted). Verdict folded
  into the gate status below.

### M8 — Slice 8: G-CANONICAL-CLOSURE (ExperimentSpec + train==eval + mandatory mechanisms) (2026-06-26)
* `src/config/experiment_spec.py` — `ExperimentSpec` (protocol/service-profile/physics/evidence/
  scene-distribution hashes + query_law + full_physics + allowed_ood_axes), `build_experiment_spec`,
  `check_train_eval_compatible` (enforces train==eval on every fingerprint unless the differing field's
  axis is in `allowed_ood_axes`; the **ideal/full-link mismatch is checked first and unconditionally** —
  never an OOD axis, constraint #9), `assert_canonical_mechanisms` (plan §4 mandatory trace flags + all
  toggleable mechanisms ON + no tau_proxy/truth-vote + full physics), `assert_headline_grounded`, and
  `build_episode_experiment_spec` (binds the profile as the single source of (k,α,β,R_d,Δ_poll) — rejects
  any ProtocolConfig/RoundPhysicsConfig that disagrees).
* `ProtocolConfig.config_hash` + `RoundPhysicsConfig.config_hash` (asdict+json, captures every PHY field
  incl. nested pathloss). Added the plan §4 mandatory trace flags (parallel_unicast, poll_window_ms,
  source_destination_accounting, collision_self_exclusion, dynamic_transient_load) to the episode trace.
* Reconciled `RoundPhysicsConfig.poll_window_s` default 0.02→**0.01 s** to equal the profile's default
  Δ_poll (10 ms) so the single-source binding is consistent (timeout still inactive at light load:
  budget = 10 slots / 2 = 5 ≥ M).
* **Tests:** `tests/config/test_experiment_spec.py` (9) + `test_episode_spec_binding.py` (7) +
  `tests/environment/test_canonical_closure.py` (4) = 20 green. Manifest slice `S8`.
* **Deferred (honest):** `run_consensus_episode` does not yet take the profile as a literal arg (binding
  enforced via `build_episode_experiment_spec`); threading it + wiring the macrostate basin objective into
  the analytic episode is Phase 5 (G-CONSTRAINED-OBJECTIVE).
* **Adversarial review (5-lens workflow, 14 agents, 189 tool-calls):** raised 8, **confirmed 4 after
  refutation — all FIXED**:
  1. [high] `headline.py::evaluate_policies_paired` defaulted to an ungrounded ideal link → now defaults
     to full physics; ideal link requires explicit `allow_ideal_ablation=True` or it RAISES (quarantine
     now *invoked* on the headline path).
  2. [high] `service_profile` + `query_law` were over-permissive OOD axes (not in the plan §12 catalogue)
     → removed; those mismatches now always block.
  3. [medium] `assert_canonical_mechanisms` could pass a bypassed ideal-link trace when
     `require_full_physics=False` → added an unconditional `link_override is not None → raise`, and made
     the physical-mechanism trace flags HONEST (gated on `full_physics`).
  4. [medium] the fingerprint test excised nested `pathloss` → strengthened to perturb every pathloss
     sub-field (the production hash was already correct via `asdict` recursion).
  Dismissed (correctly): axis-cardinality + intra-field OOD coarseness (Phase-11 concerns), and the
  single-source `run_consensus_episode` signature (documented Phase-5 deferral). Post-fix: 24 tests green.

### M10 — Slice 10: end-to-end macrostate training demo (G-CONSTRAINED-OBJECTIVE 🟢) (2026-06-26)
* `src/optimization/macrostate_objective.py::train_macrostate` — primal-dual loop: run the analytic
  episode → `macrostate_metrics` → `macrostate_lagrangian` → descend model params → ascend μ_w/μ_s/μ_d.
* **Demonstration** (two_opposing_regions + tight deadline R_d=8 + imperfect link 0.6 ⇒ the deadline basin
  is the dominant, topology-reducible failure): training raises surrogate P_correct **0.007→0.057**
  (held-out 0.006→0.060), the violated-constraint dual **μ_d ascends 10→364**, F_wrong is **not traded up**
  (stays 0 — reliability hard constraint #4), it **generalises**, and the **independent dynamic MC confirms**
  `basin_P_correct(trained) > basin_P_correct(untrained)` (1200 trials, CRN). `link_override` isolates the
  topology lever; full-physics headline training is Phase 7.
* **G-CONSTRAINED-OBJECTIVE exit met:** dual auto-responds to violation; `is_feasible` excludes infeasible
  policies before any D/E comparison; reliability never traded. Tests: 2 (training) + 4 (objective) + 9
  (surrogate) green. Manifest `S10` + `G-CONSTRAINED-OBJECTIVE-VERDICT`.
* **Deferred refinements (documented):** the profile-as-literal-arg in `run_consensus_episode` (the binding
  is already enforced by `build_episode_experiment_spec`; closure is 🟢) and retiring the analytic node-union
  F from the headline (the MC already provides the macrostate basin headline; node-union F stays a legacy
  fixed-N diagnostic next to `strict_disagreement`).

### M11 — Slice 11: overlapping correlated-evidence environment (G-CORRELATED-ENV 🟡) (2026-06-26)
* `src/environment/overlapping_evidence.py::OverlappingEvidenceModel` — `O_i = Y* ⊕ B_road ⊕ B_sensor
  ⊕ B_map ⊕ E_i`. Closed forms: `q_i=(1+μ_i)/2`, `μ_i=∏(1-2p)`; `Corr(C_i,C_j)=μ_iμ_j(1/ρ_sh²−1)/
  √((1-μ_i²)(1-μ_j²))`, `ρ_sh=∏_{shared groups}(1-2p)` (shared bits cancel since `(1-2b)²=1`). Empirically
  validated (<0.01 at 200k samples).
* **The D18 fix:** sensor/map groups are crosscutting spatial bands (x→sensor, y→map) that cut across road
  segments, so same-road peers are NO LONGER exchangeable (their correlation depends on whether they ALSO
  share a sensor/map) — verified by `test_overlapping_breaks_exchangeability`. This gives determinantal
  diversity a lever the region-block model lacked.
* **Matched-marginal control (spec C1):** `matched_marginal_shared` splits error between a shared bit and the
  node bit preserving `μ` (hence `q_i`) EXACTLY while raising covariance — `matched_marginal_low/high` have
  identical marginals, different correlation. Scenario matrix: iid / single_road / overlapping_sensor_source
  / matched_marginal_low / matched_marginal_high.
* **Honest property:** the XOR correlation is non-monotone in the shared-bit error (turns over near p=0.5, a
  max-entropy de-correlation); the strength sweep is asserted in the rising regime — documented, not a bug.
* **Contract:** C1 (structure + strength sweep + zero-structure + matched-marginal) and C2 (observable
  road/sensor/map labels, truth/proxy separated) PASS; C3 (gradient) → G-CDQ2-GRADIENT; C4 mechanism-benefit
  factorial → Phase 10 (needs CDQ 2.0). Duck-typed into the canonical episode + MC.
* **Tests:** 7 evidence + 5 scenario = 12 green under `-W error`. Manifest `S11`. Env regression **74 passed**.
* **Adversarial review (4-lens, wf_dfd24740-fd3):** the VERIFY phase hit the **monthly spend limit** (4
  verify agents failed), so the 4 review findings were UNVERIFIED, not refuted. I evaluated each solo —
  **all 4 legitimate, all FIXED + regression-tested**: (1) [real] matrix correlation NaN at a `p=0.5`
  shared bit (and scalar wrong) → reimplemented both via the direct cross-moment `E[σ_iσ_j]` (NaN-free,
  correct everywhere); (2) [doc] aligned the matched-marginal feasibility docstring to the true
  `|1-2p_target|≤|1-2p_shared|`; (3) [defensive] added input range validation; (4) [real, constraint #13]
  the `correlated_evidence` trace sentinel missed sensor/map-only correlation → added
  `has_correlated_evidence()` to both models + used it in the trace. 16 overlapping tests green under
  `-W error`.

### M12 — Slice 12: CDQ 2.0 kernel math core (G-CDQ2-MATH 🟡) (2026-06-26)
* `src/sampling/cdq2_kernel.py` — the CDQ 2.0 kernel `L = D^{1/2}(I+η ZZ^T)D^{1/2}` (full-rank
  diagonal quality `D=diag(a_j=exp s_j)` + rank-`r` diversity correction, `Z` unit-normalised rows).
  **This is the fix for the prior round's low-rank `L=BB^T` CDQ, which recovered ESP only at full
  rank `r=d`** — CDQ 2.0 has `η=0 ⇒ L=D ⇒ P_CDQ=P_ESP` EXACTLY at **any** rank `r` (the
  identifiability anchor: the model starts as ESP and learns diversity only if the env rewards it).
* **det separation** `det(L_S)=(∏_{j∈S}a_j)·det(I+η Z_S Z_S^T)` (vs explicit `|S|×|S|` `L_S`), the
  **k=2 closed form** `(1+η)²−η²(z_j·z_l)²`, inclusion `π_j=a_j ∂log e_k/∂a_j` (the diversity factor
  is `a`-independent, so the ESP homogeneity identity carries over verbatim; `Σπ_j=k`).
* **Normaliser `e_k(λ(L))` — the eigenvalue route (after audit).** I first wrote the matrix-determinant-
  lemma `[z^k]` z-series (`det(I+zL)=∏(1+zc_j)·det(I_r+ηzZ^Tdiag(c_j/(1+zc_j))Z)`, hand-verified for k=1,2;
  near-linear `O(dr²k)`). **The 5-lens adversarial audit (`wf_c696e8e5-3d6`) confirmed 5/5 findings**, and
  the z-series had a fatal flaw: the `(I+zD_c)⁻¹` geometric series makes the diversity coefficients
  alternate in sign, so assembling the (provably positive) `e_k` cancels catastrophically at wide quality
  dynamic range or large η → negative/NaN `e_k` (97/750 realistic-logit cases). **No scale cures
  differential cancellation, so I replaced the core with the eigenvalue route:** `e_k=` ESP of
  `eigvalsh(L_sym)`, `L_sym=D_c^{1/2}(I+ηZZ^T)D_c^{1/2}` (SPD), via a cancellation-free **linear** ESP
  recursion on the positive eigenvalues. **Unconditionally stable** (sum of products of positives, no
  subtraction) and **smoothly differentiable everywhere** incl. η=0 and repeated eigenvalues (`e_k` is a
  symmetric function ⇒ eigvalsh's eigenvalue-backward has no `1/(λ_i−λ_j)` gap terms). Per-source `O(d³)`
  on the `d×d` kernel — **not N×N**; bounded degree ⇒ `O(D_max²·E)` near-linear in E.
* **All 5 audit findings FIXED + regression-tested:** (#1/#2/#3 wide-range/collinear/heterogeneous
  cancellation → eigenvalue route; #4 η=0 grad detachment → eta flows through `L_sym` natively; #5
  inclusion-loss backprop wrong → eigenvalue path uses a double-differentiable linear recursion **and** the
  shared `_LogAddExp` was made double-differentiable, `-inf`-safe). The audit's complexity-noNxN lens was
  clean.
* **Tests:** `tests/sampling/test_cdq2_kernel.py` (**20**) under `-W error`: η=0⇒ESP (normaliser/subset/
  inclusion), separation, k=2, **normaliser/subset/inclusion vs brute force <1e-10** (incl. rank `r<k`,
  **wide dynamic range, collinear+large-η, heterogeneous inclusion**), **autograd vs finite-diff <1e-4**
  (a, Z, η, **η=0**, **inclusion-loss→logits**), batching, homogeneity at `d=400`. Plus 2 shared-ESP
  double-backward regressions in `test_g2_symmetric_polynomials.py`. Targeted regression **78 passed**;
  full-suite regression in flight (the `_LogAddExp` change is shared). Manifest slice `S12`.
* **Exactness boundary:** exact `k`-DPP normaliser/subset/inclusion for `0≤k≤d` (stable across wide
  dynamic range / collinear rows / large η); the determinantal quorum `P(m,n)` (spec §10) + exact `k`-DPP
  sampler are the next sub-slices (S12c/S12d) before the gate closes.

### M13 — Slice 12c: CDQ 2.0 determinantal quorum P(m,n) (G-CDQ2-MATH 🟡) (2026-06-26)
* `src/sampling/cdq2_quorum.py` — the heterogeneous correct/wrong/no-response quorum under CDQ 2.0
  (spec §10): `P(m,n) = [z^k x^m y^n] det(I+zLG)/e_k(λ(L))`, `g_j(x,y)=p⁰_j+p⁺_j x+p⁻_j y`. Evaluator
  reuses the **stable eigenvalue kernel core**: `[z^k]det(I+zLG)` at integer grid `(x_a,y_b)` =
  `e_k(λ((I+ηZZ^T)diag(c)))` with `c_j=a_j g_j` (since `eig(LG)=eig((I+ηZZ^T)D_c)`); assemble the
  `(k+1)²` log-grid, remove one **common** offset (`P=N/ΣN` is invariant to a common scale ⇒ overflow-
  free + exact), 2-D inverse-Vandermonde, zero `m+n>k`, normalise. `ΣP=1` by construction.
* **Two independent references for free:** `L=B̃B̃ᵀ`, `B̃=D^{1/2}[I|√η Z]`, so the existing low-rank
  `bruteforce_determinantal_quorum(B̃)` (subset×3ᵏ) and `determinantal_quorum_distribution(B̃)`
  (principal-minor grid) are both exact CDQ-2.0 references — matched `<1e-10`.
* **η=0 ⇒ ESP quorum exactly** (vs the diagonal-kernel `determinantal_quorum_distribution`), differentiable
  in `a,Z,η,p⁺,p⁻`, and the **diversity mechanism shifts the quorum**: uniform quality + two orthogonal
  collinear clusters of opposite correctness ⇒ η>0 spreads the poll across clusters (ESP cannot) and moves
  `P(m,n)`/`h⁺` (>1e-3).
* **Tests:** `tests/sampling/test_cdq2_quorum.py` (8) under `-W error`; full sampling suite **59 passed**.
  Manifest slice `S12c`.
* **Exactness boundary:** exact `P(m,n)` for `1≤k≤d`, per source `O((k+1)²(d³+d²r))` (eigvalsh on the `d×d`
  kernel per grid point — never N×N). **Remaining for the gate: S12d** — the exact `k`-DPP sampler (for the
  dynamic MC) + wiring the CDQ-2.0 quorum/inclusion into the bucketed canonical path (extending
  `cdq_bucketed_quorum`).
* **Adversarial review:** 4-lens find→refute workflow (`wf_bb1ada4c-747`: math-exactness / esp-and-numerics
  / differentiability / complexity-noNxN), 55 tool-calls — **0 findings, all lenses clean** (incl. the
  all-`-inf`-grid / common-offset concern: the `(x,y)=(1,1)` grid point always has `c=a>0`, so the offset
  `M` is finite). The quorum is a thin exact layer over the already-hardened eigenvalue core.

### M14 — Slice 12d: exact CDQ 2.0 k-DPP sampler (G-CDQ2-MATH 🟢) (2026-06-27)
* `src/sampling/cdq2_kernel.py::cdq2_sample` — the exact `k`-DPP sampler for the CDQ 2.0 kernel (for the
  dynamic-MC judge; no gradient). `L=D^{1/2}(I+ηZZ^T)D^{1/2}` is full-rank `d×d` SPD, so the standard
  Kulesza–Taskar eigen-sampler applies directly to `eigh(L)`: (1) pick `k` eigenvectors by the elementary-
  symmetric `k`-DPP rule, (2) elementary-DPP sample from them. Induced law = `det(L_S)/e_k(λ(L))` by
  construction. Mean quality factored out before `eigh` (overflow-safe; the law is scale-invariant).
  Per-source `d×d` — never N×N. **η=0 ⇒ the ESP elementary-symmetric subset sampler.**
* **Tests:** `tests/sampling/test_cdq2_sampler.py` (7) under `-W error`: exactly-`k`-distinct, `k>d` raises,
  empirical subset dist → exact `cdq2_enumerate_distribution` (<0.02), empirical inclusion → exact
  `cdq2_inclusion` (<0.02), η=0 → ESP inclusion, diversity avoids similar peers (analytic + empirical),
  huge-magnitude (`a~1e200`) overflow-safe + scale-invariant. Manifest slice `S12d`.
* **Independent review** (1 focused agent, 74 tool-calls, own MC at N=200k over 5 stress cases): **CORRECT,
  0 distributional defects** — all 6 scrutiny points verified vs the trusted `kdpp_sample`. One low,
  non-distributional robustness note (no mean scale-out → `eigh` overflow margin) → **fixed** (scale-out;
  law unchanged), regression added.
* **G-CDQ2-MATH closes 🟢:** kernel + ESP-degeneracy + det-separation + k=2 + exact normaliser/subset/
  inclusion + determinantal quorum `P(m,n)` + exact `k`-DPP sampler + gradients, all exact (`<1e-10` /
  MC-converged) and differentiable (`<1e-4`), eigenvalue-stable, no N×N. **Scope note:** the bucketed
  canonical wiring (CDQ2 policy into `run_consensus_episode`/MC) is **Phase 10 / G-CDQ2-EVALUATION**, where
  the ESP-vs-old-CDQ-vs-CDQ2 factorial actually exercises it; the MATH gate is the exact math, complete here.

### M15 — Slice 13: differentiable pairwise-correlation objective (G-CDQ2-GRADIENT 🟢) (2026-06-27)
* `src/sampling/cdq2_correlation.py` — the spec §11 objective `L_corr = Σ_i Σ_{j<l} π⁽²⁾_{i,jl} R_{jl}`
  = `E_{S~kDPP}[Σ_{j<l∈S} R_{jl}]` (expected within-selected-set total correlation; minimising it trains
  the diversity head Z,η to avoid co-selecting correlated peers). `R` from the overlapping env's
  `overlapping_pairwise_correlation_matrix` (deployment-observable proxy).
* **First-order-differentiable pairwise inclusion** `π⁽²⁾_{jl} = det(L_{{j,l}})·e_{k-2}(λ(L/L_{{j,l}}))/e_k`
  via the **Schur-complement quotient identity** `Σ_{S⊇T,|S|=k}det(L_S)=det(L_T)·e_{k-|T|}(λ(L/L_T))`
  (hand-verified for t=1,2) — eigvalsh + the stable positive ESP recursion, smooth first-order gradient;
  **deliberately NOT** a 2nd-order autograd of `e_k` (the training backprop would make that a fragile
  3rd-order op at degenerate eigenvalues). No `float()/.item()/detached` score on the path.
* **Tests:** `tests/sampling/test_cdq2_correlation.py` (8) under `-W error`: `π⁽²⁾` vs brute force <1e-10
  (incl. r<k), consistency identities (`Σ_{l≠j}π⁽²⁾_{jl}=(k-1)π_j`, `Σ_{j<l}π⁽²⁾=C(k,2)`), η=0⇒ESP,
  `L_corr` vs brute force, **autograd vs finite-diff <1e-4** (a,Z,η), no-forbidden-ops (inspected), and the
  **C3 matched-marginal discrimination**.
* **Adversarial audit** (`wf_8f8422d1-5ad`, 4-lens): schur-exactness + gradient-purity **clean**; **1
  confirmed** (medium, tests-only) — the C3 test was *vacuous* (`matched_marginal_low` gives an identically-
  zero R, so the cost, being linear in R, made the lo-arm gradient bit-exactly 0 → a presence-not-
  discrimination check). **Fixed:** rebuilt with two *non-zero* matched-marginal arms + a **heterogeneous
  (block) R** + group-aligned Z. (Discovered while fixing: a *uniform* R gives `dL_corr/d-policy=0` because
  `Σπ⁽²⁾=C(k,2)` — diversity has no lever against **exchangeable** correlation; the heterogeneity is exactly
  the D18 fix.) Plus **1 refuted-but-hardened** (overflow at extreme quality → mean scale-out, distribution-
  preserving since `π⁽²⁾` is a scale-invariant ratio).
* **Closes the overlapping environment's C3** (correlation gradient reaches + discriminates covariance under
  matched marginals). C4 (mechanism-benefit factorial) remains Phase 10. Manifest `S13` + verdict.

### M16 — Slice 14: bucketed CDQ 2.0 canonical wiring (2026-06-27)
* `src/sampling/cdq2_wiring.py` — `cdq2_edge_inclusion` + `cdq2_bucketed_quorum` (the CDQ 2.0 analogue
  of `cdq_query.py`) on the degree-bucketed layout (padded cells ≤2E, no N×N), plus `CDQ2Policy`
  (quality `exp(s)`, diversity `Z`, strength `η`). Additive `"cdq2"` dispatch in `run_consensus_episode`
  and `run_dynamic_mc` (+ `_CDQ2SubsetSampler` enumerating the exact CDQ 2.0 k-DPP law). This is the
  prerequisite that lets CDQ 2.0 run end-to-end for the **Phase 10** factorial.
* **Exact padded-slot exclusion:** the bucket `slot_mask` is threaded as an optional `mask` into the
  CDQ 2.0 kernel — a padded slot (`a=0`) gets an EXACTLY-zero kernel row (zero eigenvalue ⇒ 0 to `e_k`,
  inclusion 0), **better than** the old CDQ's `sqrt(clamp_min(eps))` ~eps approximation.
* **η=0 ⇒ L=diag(a) EXACTLY** (any `Z`), so the CDQ 2.0 episode reproduces the ESP episode **bit-for-bit**
  (`S_allcorrect/F_wrong/F_disagree/c_ir` <1e-9) and the η=0 MC subset law equals the ESP law (<1e-10).
* **Tests:** `tests/sampling/test_cdq2_wiring.py` (9) under `-W error`; broad regression
  (sampling+canonical_episode+validation) **120 passed** — the additive dispatch is non-regressing.
* **Adversarial review** (1 focused agent, own reproducers + 200k-draw MC): 3/4 concerns clean; **1
  confirmed [medium]** — the `cs_safe` NaN-guard covered only *padded* slots, but a *real* candidate whose
  deformed quality `c=a·g` hits exactly 0 (`p0=0` at an ideal link `ell=1`) still fed `sqrt(0)` ⇒ **NaN
  backward** (`link_override=1.0` episode + standalone quorum at `p⁺+p⁻=1` reproduced it). The headline
  path (`ell<1`) was safe, but the ideal-link ablation was not. **Fixed at the root:** sanitize *any*
  `cs=0` via `pos=(mask & cs>0)`, **and** clamp `log(e_k)` for the all-excluded grid corner (`log(0)=-inf
  × upstream-0 = 0·inf`). Regressions added (ideal-link backprop + quorum-grad-at-`p0=0`). The old CDQ never
  NaN'd here — CDQ 2.0's exact-no-eps design had traded that robustness away; the `pos`-sanitiser restores
  it *without* the eps inexactness. Manifest `S14`.

### M17 — Slice 15: CDQ 2.0 mechanism-benefit factorial (G-CDQ2-EVALUATION 🟢, user Option 1) (2026-06-27)
* `docs/gate_evidence/macrostate/run_cdq2_factorial.py` → `cdq2_factorial_results.json` — the fair,
  matched-marginal MC factorial (Phase 10). ESP and CDQ 2.0 share the SAME distance-based quality
  (ESP==CDQ2 η=0); the only difference is the diversity correction (η=8, OBSERVABLE sensor-group Z).
  Arms iid / matched_marginal_low (zero cov) / matched_marginal_high (pos cov, IDENTICAL marginal);
  fixed-link 0.85 + full physics; 6×3000 / 3×3000 trials; pooled Wilson CIs. Independent dynamic-MC
  basin outcomes are the headline judge.
* **Result (honest, robust across 3 exploratory regimes + the rigorous run):**
  - **Scoped P_correct benefit CONFIRMED + CI-separated + matched-marginal-controlled:** in
    matched_marginal_high CDQ2 P_correct `[0.634,0.648]` vs ESP `[0.618,0.632]` (fixed-link, disjoint
    CIs; full physics +0.018); in iid/mm_low (no cov) CDQ2≈ESP (CIs overlap). ESP cannot distinguish
    the identical-marginal high/low arms; CDQ2 can ⇒ the benefit is **covariance-driven and scoped**
    (the plan's "CDQ wins only in overlapping correlation ⇒ mechanism effective & scoped" + C4).
  - **BUT the channel is FASTER QUORUM (F_deadline −0.025..−0.028), NOT the intended F_wrong reduction.**
    F_wrong is **not** lowered — point estimate consistently **up** (+0.009 fixed / +0.014 full). So the
    operative mechanism is "diversity → broader reach → faster quorum", **not** "diversity → less
    redundant evidence → fewer WRONG decisions".
  - **Mechanistic (fundamental, not tuning):** in a MAJORITY-CORRECT regime, polling diversely raises a
    node's exposure to the MINORITY correlated-wrong clusters → slightly more F_wrong; it only rescues
    the few nodes already in wrong clusters. F_wrong rises monotonically with η (η→0⇒ESP), so no η helps.
  - **Surrogate fidelity:** the sensor-only oracle Z is the *upper bound* on any Z trained on the S13
    correlation cost; even it doesn't reduce F_wrong ⇒ training on the correlation surrogate would not
    improve (slightly worsen) F_wrong. Surrogate & MC **agree** on P_correct, **disagree** on F_wrong.
* **Resolution (user Option 1, 2026-06-27):** I reported the nuanced result via STOP+REPORT; the user
  chose to **accept the scoped P_correct win** per the plan's "mechanism effective & scoped" rule. So
  G-CDQ2-EVALUATION is 🟢 **with the F_wrong caveat documented (not claimed)**, closing the env's **C4**.
  Added the reusable harness `src/evaluation/cdq2_factorial.py` (`observable_group_diversity` [C2,
  truth-independent], `run_factorial_cell`, `esp_vs_cdq2_cell`, `wilson_ci`) + `overlapping_sensor_source`
  to the evidence run (same scoped-positive / F_wrong-up pattern), + `tests/evaluation/test_cdq2_factorial.py`
  (6 honest tests, **no F_wrong-reduction asserted**). The central "lowers F_wrong/F_split" framing is NOT
  claimed; the negative F_wrong result is on record. Manifest `S15` + `G-CDQ2-EVALUATION-VERDICT`.

### M19 — Slice 17: temporal memory (G-TEMPORAL 🟢, ALL GATES GREEN → stop-condition #8) (2026-06-27)
* `src/metrics/temporal_memory.py` (`causal_ema`, `no_memory`, `estimate_quality`) +
  `src/environment/temporal_sequence.py` (`TemporalCorrelationSequence`) +
  `docs/gate_evidence/macrostate/run_temporal_factorial.py` → `temporal_factorial_results.json` +
  `tests/test_temporal.py` (9). The static mainline being complete, this adds a **causal, differentiable,
  observable-driven EMA memory** `m_t=(1-ρ)m_{t-1}+ρx_t` over a persistence-controlled, matched-marginal-
  in-time correlated-evidence sequence, driving the CDQ 2.0 diversity.
* **Mechanism Contract C1–C5 all PASS:** C1 (persistence knob + active-band schedule + matched-marginal-
  in-time), C2 (observable per-band proxy, truth-independent + **causal: zero gradient w.r.t. future**),
  C3 (differentiable in x and ρ; reaches CDQ params; no `float()/.item()/detach`), C4 (matched-marginal-in-
  time control), C5 (ρ=1 / η=0 ⇒ static mainline). The memory **tracks persistent structure** —
  estimate-quality high under persistence, ≥0.2 lower under iid-in-time (scoped, matched-marginal-controlled).
* **Honest basin result (the headline judge):** at the MC macrostate basin first-hitting, the memory-driven
  CDQ 2.0 diversity does **not** beat ESP — mean P_correct ESP 0.654 vs memory 0.644 / no_memory 0.641 /
  oracle 0.634 (persistent); all diversity variants marginally **below** ESP, oracle even slightly worse.
  **Inherits the S15 caveat:** the diversity's *basin* payoff is marginal/regime-dependent. The temporal
  contribution is the structure-**tracking** memory (estimate level), **not** a basin-reliability gain —
  reported, not hidden. (The diversity construction was corrected first: the kernel unit-normalises Z, so
  the estimate must change z's *direction*, not magnitude.) Manifest `S17` + `G-TEMPORAL-VERDICT`.

### Iteration checkpoint #12 — ALL 11 GATES GREEN → stop-condition #8 (2026-06-27)
**The macrostate / CDQ 2.0 round is COMPLETE — all eleven gates green:** G-P0-PHYSICS, G-CANONICAL-CLOSURE,
G-MACROSTATE, G-CONSTRAINED-OBJECTIVE, G-CORRELATED-ENV (C1–C4), G-ESP-BASELINE, G-CDQ2-MATH, G-CDQ2-GRADIENT,
G-CDQ2-EVALUATION (🟢-caveat), G-SCALE-GENERALIZATION, G-TEMPORAL (🟢-caveat). Per stop-condition #8 I stop
and report. **Honest round headline:** the CDQ 2.0 mechanism is mathematically exact (η=0≡ESP, brute-force
<1e-10), differentiable (<1e-4), identifiable (all 5 Contract items), scale-generalising (N≤10⁴, no N×N),
and works at the **query / gradient / estimate** level; but its **macrostate-basin reliability payoff in the
snowball consensus is marginal/regime-dependent** (a CI-separated but small, deadline-channel, scoped
P_correct gain in S15; a null in the temporal S17; F_wrong not reduced). **The paper-headline framing of the
CDQ 2.0 contribution — given this documented basin caveat — is the user's final call (the freeze can lift,
but I will not change the paper headline).**

**Resolution (user-decided 2026-06-27): Plan A** — frame the contribution as the *exact-ESP-containing,
mechanism-identifiable, differentiable, scale-generalising diversity query family (CDQ 2.0) + the
differentiable pairwise-correlation objective methodology*, with the basin-reliability payoff honestly
scoped (small, covariance-scoped, deadline-channel `P_correct` gain; not an `F_wrong/F_split` reduction).
Contribution/results writeup produced at **`docs/CDQ2_RESULTS_AND_CONTRIBUTION.md`** (synthesised from the
S1–S17 evidence; the legacy node-union/global-risk paper headline is left untouched). **Round complete.**

### M18 — Slice 16: scale + OOD generalization (G-SCALE-GENERALIZATION 🟢) (2026-06-27)
* `docs/gate_evidence/macrostate/run_scale_generalization.py` → `scale_generalization_results.json` +
  `tests/test_scale_generalization.py` (6). `src/config/experiment_spec.py` now accepts `query_law="cdq2"`.
* **Near-linear, no N×N (bounded-degree V2X regime):** canonical episode (ESP + CDQ 2.0) timed at
  **N=120…9840** (the plan's 100…10000) — log-log runtime slope **0.88 (ESP) / 0.81 (CDQ2)**, ~linear at
  the large end; **maxdeg constant at 12**, `total_cells ≤ 2E` at every N, `E ∝ N`. CDQ 2.0 is a ~2×
  constant factor with the **same** slope. **No N×N is structural, not just empirical** — grep over `src/`
  for `(N,N)`/`num_nodes×num_nodes`/`eye(N)` allocations returns NONE; the path is sparse radius graphs +
  the bucketed `[m,w]` layout + per-source `[d,d]` kernels (d=bounded degree). (Timing used `link_override`
  to isolate the algorithm from the FBL constant; FBL is itself per-edge O(E), so full physics is also
  near-linear.)
* **OOD-axis enforcement matrix:** scaling N is exactly the registered **`node_count`** axis — the
  protocol/service-profile/physics hashes are **constant across N**, only `scene_distribution_hash` varies.
  `check_train_eval_compatible`: node_count registered → **allow**; unregistered → **block**; a protocol
  mismatch (non-OOD) → **block** even with node_count registered; an ideal/full-link mismatch →
  **always block** (constraint #9). All four cells verified.
* **Headline at scale:** the macrostate basin first-hitting (four basins sum to 1, `P_correct∈(0,1)` in the
  correlated regime) works at N=336 via the independent dynamic MC (not a node-union metric); CDQ 2.0
  η=0==ESP holds at N=300 (not just dev size). Self-audit clean (no new math; honest near-linear framing;
  deferred O(d³) all-pairs only needed for high-degree dense graphs, not a scale blocker here). Manifest
  `S16` + `G-SCALE-GENERALIZATION-VERDICT`.

### Iteration checkpoint #11 — G-SCALE-GENERALIZATION 🟢 (2026-06-27)
**Ten gates green**; only **G-TEMPORAL (Phase 12)** remains. The macrostate / CDQ 2.0 round is near
complete: P0 physics, canonical closure, macrostate basin evaluator, reliability-constrained objective,
overlapping correlated-evidence environment (C1–C4), CDQ 2.0 kernel/quorum/sampler, differentiable
correlation objective, fair MC factorial (scoped P_correct benefit, F_wrong-caveat documented), and now
near-linear scale + OOD generalization. **Next: Phase 12 / G-TEMPORAL** — temporal memory for drift /
correlation / load (static mainline first), then the round closes (all gates green ⇒ the paper-headline
freeze can lift, pending the user's framing of the CDQ 2.0 contribution given the F_wrong caveat).

### Iteration checkpoint #10 — G-CDQ2-EVALUATION 🟢 (with caveat) + env C4 closed (2026-06-27)
**Nine gates green** (G-P0-PHYSICS, G-CANONICAL-CLOSURE, G-MACROSTATE, G-CONSTRAINED-OBJECTIVE,
G-CORRELATED-ENV [C1–C4 closed], G-CDQ2-MATH, G-CDQ2-GRADIENT, **G-CDQ2-EVALUATION 🟢-with-caveat**).
The CDQ 2.0 contribution is end-to-end: kernel + quorum + sampler + differentiable correlation objective
+ canonical wiring + the fair matched-marginal MC factorial. **Honest headline:** CDQ 2.0 delivers a
CI-separated, covariance-scoped P_correct benefit (the mechanism is effective and scoped, matched-marginal-
controlled) via faster quorum; it does NOT reduce the F_wrong reliability basin (documented boundary). **All
5 Mechanism Contract items evidenced** (C1/C2 S11, C3 S13, C4 S15, C5 S1/S8). **Next: Phase 11 /
G-SCALE-GENERALIZATION** — N=100…10000 + OOD axes under a fixed protocol/service-profile (and the deferred
O(d³) pairwise-inclusion / quorum scale optimisations), then Phase 12 / G-TEMPORAL.

### Iteration checkpoint #9 — bucketed CDQ 2.0 wiring landed (2026-06-27)
**Eight gates green; S14 lands the CDQ 2.0 canonical wiring (Phase-10 prerequisite).** CDQ 2.0 now runs
end-to-end in both the analytic episode and the dynamic MC, η=0 reproducing ESP bit-for-bit, with exact
padded exclusion and NaN-safe ideal-link gradients (audit-fixed). **Next: Phase 7 / G-ESP-BASELINE** (the
full-physics multi-seed ESP baseline — a run on the now-unified pipeline) and **Phase 10 / G-CDQ2-EVALUATION**
(the ESP-vs-old-CDQ-vs-CDQ2 × structure-on/off mechanism-benefit factorial + matched-marginal control, with
the **dynamic-MC basin outcomes as the headline judge** — must show CDQ 2.0 lowers basin `F_wrong`/`F_split`
vs ESP in the heterogeneous-correlation environment without trading reliability). Then G-SCALE-GENERALIZATION
(Phase 11) and G-TEMPORAL (Phase 12).

### Iteration checkpoint #8 — G-CDQ2-GRADIENT 🟢 + env C3 closed (2026-06-27)
**Eight gates green: G-P0-PHYSICS, G-CANONICAL-CLOSURE, G-MACROSTATE, G-CONSTRAINED-OBJECTIVE,
G-CORRELATED-ENV (env-level + **C3 now closed**), G-CDQ2-MATH, and G-CDQ2-GRADIENT 🟢.** This session
added S13 (the differentiable pairwise-correlation objective). The audit caught a *vacuous* C3 test
(zero-R low arm) — fixed into a genuine heterogeneous matched-marginal covariance-discrimination test;
the deeper lesson (uniform/exchangeable correlation ⇒ zero diversity gradient) reconfirms why the
overlapping env's crosscutting common causes (D18 fix) are necessary. **Next: Phase 7 / G-ESP-BASELINE**
(offline full-physics multi-seed ESP baseline — no new code, a run) and **Phase 10 / G-CDQ2-EVALUATION**
(the mechanism-benefit factorial ESP-vs-old-CDQ-vs-CDQ2 + matched-marginal, which also lands the bucketed
CDQ2 canonical wiring). Then G-SCALE-GENERALIZATION (Phase 11) and G-TEMPORAL (Phase 12).

### Iteration checkpoint #7 — G-CDQ2-MATH 🟢 (kernel + quorum + sampler) (2026-06-27)
**Seven gates green: G-P0-PHYSICS, G-CANONICAL-CLOSURE, G-MACROSTATE, G-CONSTRAINED-OBJECTIVE,
G-CORRELATED-ENV (env-level), and now G-CDQ2-MATH 🟢.** This session: **S12 (kernel core) + S12c
(determinantal quorum) + S12d (sampler)**. The kernel audit found **5/5 real defects** — most importantly
the det-lemma z-series' catastrophic cancellation at realistic GNN logit ranges, which I replaced with the
unconditionally-stable **eigenvalue route** (`e_k=ESP(eigvalsh(L_sym))`) — plus an η=0 gradient detachment
and a shared `_LogAddExp` double-backward bug; **all fixed**, full 359-test regression green. Quorum audit
**0 findings**; sampler review **0 distributional defects**. **Next: Phase 9 / G-CDQ2-GRADIENT** — the
differentiable pairwise-correlation objective `L_corr=Σ_i Σ_{j<l} π^(2)_{i,jl} R_{jl}` (pairwise inclusion
`π^(2)` via an explicit **leave-two-out first-order-differentiable** formula on the CDQ 2.0 kernel, `R` from
`overlapping_pairwise_correlation_matrix`), closing the env's **C3** gradient contract — no
`float()/.item()/detached` score on the training path. Then Phase 7 (ESP full-physics baseline) and Phase
10 (G-CDQ2-EVALUATION: the mechanism-benefit factorial + matched-marginal, which also lands the bucketed
CDQ2 wiring).

### Iteration checkpoint #6 — G-CORRELATED-ENV 🟢 (env-level) (2026-06-26)
**Five gates: G-MACROSTATE 🟢, G-P0-PHYSICS 🟢, G-CANONICAL-CLOSURE 🟢, G-CONSTRAINED-OBJECTIVE 🟢,
G-CORRELATED-ENV 🟢 (env-level; C3/C4 downstream).** Completed S1–S11. The overlapping common-cause env
(the D18 fix) + matched-marginal control are in, audit-addressed (the audit's verify phase was spend-limited;
I evaluated + fixed all 4 findings solo). **Note: subagents are spend-blocked again** (the verify phase hit
the monthly limit) — the next iteration may run solo. **Next: Phase 8 / G-CDQ2-MATH** — the CDQ 2.0 kernel
`L = D^{1/2}(I+η ZZ^T)D^{1/2}` with `η=0` EXACTLY recovering ESP (the fix for the old low-rank `BB^T` CDQ not
containing ESP), exact subset/quorum probabilities + gradients vs brute force, near-linear in E. (Phase 7
ESP baseline is an offline full-physics multi-seed run needing no new code; Phase 8 math is the implementable
central contribution.)

### Iteration checkpoint #5 — G-CONSTRAINED-OBJECTIVE 🟢 (2026-06-26)
**Four gates green: G-MACROSTATE, G-P0-PHYSICS, G-CANONICAL-CLOSURE, G-CONSTRAINED-OBJECTIVE.** Completed
S1–S10. **Next: Phase 6 / G-CORRELATED-ENV** — the overlapping common-cause evidence environment
(`O_i = Y* ⊕ B_road ⊕ B_sensor ⊕ B_map ⊕ B_temporal ⊕ E_i`, spec §7) with MATCHED-MARGINAL controls
(same marginal correctness + geometry + link-quality, different covariance) and the Mechanism Contract
C1–C4 evidence — the environment that finally gives determinantal diversity (CDQ 2.0) a lever, fixing the
prior round's D18 "near-exchangeable region-block" obstacle. Then Phase 7 (ESP baseline) and Phase 8
(CDQ 2.0 `L=D^{1/2}(I+ηZZ^T)D^{1/2}`).

### M9 — Slice 9: macrostate constrained objective (G-CONSTRAINED-OBJECTIVE 🟡→🟢) (2026-06-26)
* **Design judge-panel workflow** (wf_f37372a9-061): 4 propose + 4 judge completed (synth agent failed the
  StructuredOutput retry cap → I synthesized from the transcripts). Top two (both 27/30) were
  first-passage-hazard designs with Gaussian-CLT occupancy. Synthesized design:
  CLT occupancy + increment-share first-passage + bivariate-Mehler split + Rockafellar CVaR.
* `src/metrics/basin_surrogate.py` — differentiable Level-2 surrogate for the macrostate basin
  first-hitting: `mu_C=Σω_i c_i`, `σ²_C=Σω_i² c_i(1-c_i)`, `g_C=Φ((μ_C-ρ_f+cc)/σ_C)` (cc=½·max ω,
  continuity correction), increment-share first-passage (four outcomes **sum to 1 exactly**,
  telescoping), bivariate-normal Mehler split (`ρ_CW≤0` suppresses), Rockafellar `CVaR_q(T_confirm|O=C)`.
  Validated vs an INDEPENDENT Poisson-binomial exact occupancy (within 5% at N=40).
* `src/optimization/macrostate_objective.py` — `macrostate_metrics` (the four basins + CVaR/mean confirm
  + deadline-capped unconditional latency + energy per attempt/success), `macrostate_lagrangian`
  (CVaR+λE+Σμ_x(F_x−ε_x)), `MacrostateDuals` (μ_w/μ_s/μ_d ascent), `is_feasible` (hard-constraint filter,
  reliability never traded). Replaces the legacy node-union F/D/E objective.
* Fixed the pre-existing `float(grad-tensor)` warnings (dynamic_mc detaches report-only time/energy;
  primal_dual uses a detach-safe `_to_float`).
* **Exactness boundary:** Level-2 differentiable surrogate (CLT/Gaussian-closure/soft-CVaR); the dynamic
  MC (S4) is the headline judge. **Tests:** 9 surrogate + 4 objective green. Manifest slice `S9`.
* **Adversarial review** (5-lens: differentiability / mass-conservation / faithfulness / cvar-latency /
  objective-hardness) running (wf_5292ab28-0d8). Targeted regression (optimization+validation+metrics)
  running to confirm the warning fixes + new modules.
* **Adversarial verdict (5-lens, wf_5292ab28-0d8):** raised 2, **0 confirmed**. Both dismissed (the
  faithfulness "A overshoots" only on physically-infeasible `c_i+w_i>1` inputs; real marginals satisfy
  `c_i+w_i≤1` ⇒ basins disjoint) but **hardened anyway**: validate the ω sums, document the `c+w≤1`
  precondition, clarify `is_feasible` (surrogate = training check; MC = headline judge). 13 tests pass under
  `-W error::UserWarning`; targeted regression **79 passed**.
* **Remaining for the gate:** end-to-end training demo (dual ascent enforces constraints + training lowers
  the MC's basin `F_wrong` toward the topology-oracle), thread the profile into `run_consensus_episode` as
  the literal single source.

### Iteration checkpoint #4 — G-CANONICAL-CLOSURE 🟢 (2026-06-26)
**Three gates green: G-MACROSTATE 🟢, G-P0-PHYSICS 🟢, G-CANONICAL-CLOSURE 🟢.** Completed S1–S8.
G-CANONICAL-CLOSURE closed by S8 + a 5-lens adversarial audit (8 raised, 4 confirmed, **all fixed**:
ungrounded ideal-link headline default, over-permissive OOD axes, ideal-link mechanism-gate hole, nested
pathloss fingerprint coverage). Pre-fix full regression **206 passed**; post-fix affected suites 24 passed;
definitive post-fix full regression in flight. **Next: Phase 5 — G-CONSTRAINED-OBJECTIVE**: thread the
ConsensusServiceProfile into `run_consensus_episode`, replace the analytic node-union F with the macrostate
basin occupancy/hazard, and implement `min CVaR_q(T_confirm|O=C)+λE s.t. F_wrong/F_split/F_deadline ≤ ε`
via primal-dual on the three duals (the macrostate basin outcome becomes the headline).

### Iteration checkpoint #3 — G-P0-PHYSICS 🟢 (2026-06-26)
Completed this session: **S1–S7**. **Two gates green: G-MACROSTATE 🟢 and G-P0-PHYSICS 🟢.**
G-P0-PHYSICS closed by P0-F + a 7-lens adversarial verification workflow that raised **0 findings**
(collision / source-dest / poll-window / delay / MC-independence / differentiability-complexity /
truth-leak), 20 P0 tests + the 94-test broad regression all green. The spend limit lifted mid-session,
so workflow orchestration is available again (the P0-E design panel had been spend-blocked; P0-E was
done solo, P0-F + the audit used workflows). **Next:** **G-CANONICAL-CLOSURE** — make
`ConsensusServiceProfile` the single source feeding one `run_consensus_episode`; add an `ExperimentSpec`
with protocol/profile/physics/evidence/scene hashes enforced train==eval; quarantine ideal-link to an
explicit ablation; error on unused config — then **Phase 5** macrostate constrained objective
(CVaR tail-latency + energy, primal-dual on wrong/split/deadline) wiring the macrostate basin outcome as
the headline (replacing the legacy node-union F in the analytic episode).

### Iteration checkpoint #2 (2026-06-26)
Completed this session through P0-E: **S1–S6**. Physics+canonical regression after P0-E: **26 passed**;
broad regression **94 passed**. (The P0-E design judge-panel workflow had been blocked by the monthly
spend limit; implemented solo. Spend limit later lifted.)

### Iteration checkpoint #1 (2026-06-26)
Completed earlier this session: **S1–S5**. Gate posture: **G-MACROSTATE 🟢** (evaluator fully validated,
Level-1 exact == Level-3 MC); **G-P0-PHYSICS** P0-A/B/C/D done (P0-E/F remain); **G-CANONICAL-CLOSURE**
profile + hash done (wiring remains). Full physics-dependent regression green (90 passed). No stop
condition hit. **Next:** P0-E unified poll-window `ℓ(Δ_poll)` with an explicit within-window
completion/timeout factor (needs a service-time distribution: HARQ retx count + M/M/1 queue delay →
`P(T_req+T_resp ≤ Δ_poll)`), then P0-F analytic/MC alignment, then G-CANONICAL-CLOSURE ExperimentSpec
hashing (train==eval enforcement) and the macrostate-objective rewrite (Phase 5).

---

## Guarded-CDQ2 round — decision log

### GM0 — round bootstrap + Phase 0 freeze (2026-06-27)
* Read the two new live specs (`GUARDED_CDQ2_TECHNICAL_SPEC.md`, `GUARDED_CDQ2_ENGINEERING_PLAN.md`) +
  the contract + the prior progress + S15 factorial JSON. Confirmed the 7 new gates and the round thesis
  (CDQ2 = liveness extension, ESP = reliability-first default, validity–liveness trade-off **guarded**).
* **Phase 0 freeze:** git is now initialised, so the plan's "tag current state" is real — created annotated
  tag **`macrostate-cdq2-v2-before-guarded`** at `abda600` (the completed 11-gate macrostate round).
* Recorded the new gate table + adopted guard defaults (δ_w=δ_s=2e-4, T_w=T_s=1e-4) at the top of this doc.

### GM1 — Slice GS1: metric namespace + result schema (G-METRIC-NAMESPACE 🟢) (2026-06-27)
* `src/metrics/namespaces.py` — the single source of truth for the spec §7 namespaces
  (`macro`/`strict_audit`/`diagnostic`/`sampling`/`cdq`/`runtime` + legacy `surrogate_*`), the canonical
  per-namespace key vocabularies, the **exact-match** forbidden-bare ban-list (`F`, `F_wrong`, `F_disagree`,
  `S_allcorrect`, `failure`, `reliability`, `D`, `delay`, `P_correct` — `macro_F_wrong` is fine, bare
  `F_wrong` is not), and recursive `iter_keys` + concept-based `is_legacy_key` (node-union/all-correct/
  global-product spellings, not just the `surrogate_` prefix).
* `src/metrics/schema.py` — `macro_block` (four outcomes, **finite + sum-to-1** enforced), `macro_delta_block`
  (`_delta`-suffixed so deltas aren't mistaken for outcomes), `build_result_record` (§7.4: version + policy +
  query_family + namespaced blocks; legacy gated behind `allow_legacy=True`), `validate_result`
  (version + **top-level whitelist** + per-block namespace + **whole-record legacy scan**, headline mode
  forbids any surrogate), `assert_no_legacy_metrics` (the figure-script guard, constraint #13),
  `migrate_legacy_factorial_cell` (pure key-rename shim, no recomputation).
* **Migrated** the S15 factorial → namespaced `cdq2_factorial_namespaced.json` (16 records validated, 0
  forbidden/legacy keys) via `migrate_s15_to_v2.py`; **S15 preserved** (archived to
  `…/macrostate/archive/`, original untouched — Phase 0 "do not overwrite S15"). Added namespaced
  converters to `DynamicMCResult` (basins→`macro_block`) and `FactorialResult` (additive, non-breaking).
* **Adversarial audit (1 general-purpose reviewer):** raised **2 CRITICAL** (both real, both FIXED +
  regression-tested): (#1) `validate_result(headline)` let a `surrogate_*` metric sit at top level or under
  a foreign key — fixed with a top-level whitelist + a whole-record legacy scan; (#2) a NaN macro outcome
  bypassed sum-to-1 (`abs(nan−1)>tol` is False) — fixed with a finiteness check. Plus 1 MODERATE (concept-
  blind legacy detection → broadened) + 2 hardening (`iter_keys` traverses Mapping/set; builder rejects
  incomplete macro). All six exploit paths now have regression tests.
* **Tests:** `tests/metrics/test_namespace_schema.py` (27 under `-W error`) — ban-list exactness, sum-to-1,
  version, legacy gating, figure-guard, migration, the old-S15-JSON-is-rejected check, both converters, and
  the six audit regressions. Regression: `tests/metrics/` + `tests/evaluation/` + macrostate-MC = green.
  Manifest `docs/gate_evidence/guarded_cdq2/manifest.json` slice `GS1`.
* **Exit met:** all NEW-round experiment scripts will emit only namespace-clean `macrostate_v2` records;
  ambiguous/legacy keys cannot reach a headline JSON; figures fail on legacy input. The frozen prior-round
  `run_cdq2_factorial.py` is left byte-identical (it reproduces S15); the migration shim is the bridge.
* **Next: G-RESULT-MANIFEST** — make the §7.4 hashes (physics/profile/evidence/scene/policy/checkpoint +
  query_family) mandatory, with fail-fast on train/eval physics mismatch (unless declared OOD), missing
  macro outcomes, and untracked model seed. The schema's `hashes` slot + `build_result_record` already
  accept them; the next gate enforces presence + consistency.

### GM2 — Slice GS2: result manifest + hash enforcement (G-RESULT-MANIFEST 🟢) (2026-06-27)
* `src/metrics/manifest.py` — the enforcement layer over the schema's `hashes` slot:
  - `build_manifest(spec, *, policy_hash, checkpoint_hash, model_seeds, git_commit/manifest_id)` assembles
    the §7.4 manifest from an `ExperimentSpec` (reusing its deterministic config hashes — **no new hashing
    math**) + the policy/checkpoint fingerprints + the tracked training seeds.
  - `validate_manifest(record, *, require_seeds, min_seeds, headline)` fails fast on any missing/empty
    required hash (`physics`/`service_profile`/`evidence`/`scene_distribution`/`protocol`/`policy`/
    `checkpoint`/`experiment_config`), a missing provenance id (git commit **or** manifest id), a missing
    `query_family`, or **untracked/duplicate/too-few model seeds** (the "no single-seed headline" shortcut
    is blocked via `min_seeds`, default headline ≥ 5). Also runs `validate_result` (version + namespaces +
    macro completeness).
  - `assert_train_eval_consistent(record, train, eval)` delegates to `check_train_eval_compatible` (the
    existing C5 train==eval guard: physics/protocol/profile/evidence/scene/query must match unless a
    **registered OOD axis** permits it; the ideal/full-link distinction **always** blocks — constraint #9)
    **and** binds the recorded hashes to the eval spec, so a result cannot be relabelled with a spec it did
    not actually run under (tamper check).
* **Tests:** `tests/metrics/test_result_manifest.py` (17 under `-W error`) — every required-hash drop, empty
  value, missing provenance, untracked/duplicate/too-few seeds, the physics-mismatch fail-fast (+ OOD-axis
  release), the unconditional ideal/full-link block, the recorded-hash tamper check, and a real-config
  end-to-end build. Combined metrics suite 44 green.
* **Exit met:** the machinery is in place + tested; each new-round experiment writer (ESP scale, η-curve,
  guarded, hazard) calls `build_manifest` + `validate_manifest` + `assert_train_eval_consistent` at write
  time, so the gate bites on real evidence as those gates land. Self-review: no new hashing (reuses
  `experiment_spec`), no circular import (manifest → experiment_spec + schema; neither imports manifest).
* **Next: G-ESP-PERFORMANCE-SCALE** — the heavy gate: trained ESP/ESD-GNN checkpoints (≥5 model seeds)
  evaluated for **real macrostate-basin outcomes** (not runtime) across N=100…10000, fixed-protocol vs
  fixed-service-profile, with scale-regret + feasibility-retention, dynamic-MC judged, UCB for rare failure.
  Deserves its own iteration(s) — needs a trainable ESP/ESD-GNN checkpoint path at multiple scales.

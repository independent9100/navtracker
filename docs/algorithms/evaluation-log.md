# Evaluation Log

Running record of measured comparisons between estimator / associator
alternatives and the baseline. Each entry records the scenarios run, the
numbers, and a one-line takeaway. Predictions go in the algorithm docs;
this file holds *observations* only.

Tracker configuration unless noted: `ConstantVelocity2D(q=0.1)`,
`GnnAssociator`, `TrackManager`, baseline thresholds from the scenario tests.

## 2026-07-12 — Cl-4 endgame Part 2: 2-D price surface + phantom map — dials are iso-cost but spatially DIFFERENT; W25/f0.10 = amended knee candidate [Cl-4]

Amended-ticket second half (user's spatial split); merged 7080949.
Write-up: `docs/baselines/2026-07-11_cl4_cliff_price_list.md` Part 2.

- **Geography (exact signed distance):** env-2 vessels ride 6–42 m offshore
  (median ~25–31 m), never inland. philos in-band radar: 1361/1706 returns
  are INLAND structure (gated regardless); the 345 offshore water-clutter
  returns span 0–50 m — dense at 0–10 m, tail of 41 at 40–50 m. Density
  gradient, no clean inner/outer cut → the split buys no discount.
- **2-D surface (W_off × floor, 24 cells):** narrowing W_off shifts the
  env-2 revival cliff to higher floors (8/8 holds to f0.10 at W_off ≤ 25 m)
  but the philos bill tracks one-for-one — iso-cost ridges; cheapest 8/8 ≈
  +17 card_err either way (W25/f0.10 +17.35 ≈ W50/f0.08 +19.35). env-1
  (16.57) and harbor (9.53) unchanged at every cell.
- **Phantom MAP (the discriminator):** narrowing W_off adds phantoms
  almost entirely IN-STRIP (in-strip 37→228, far field 88→88 flat, max
  264 m). Lowering the floor SPILLS into open water (far 88→117, max
  5000 m flyers). Same price, different placement — the spatial split is
  partially vindicated: not a cheaper door, a spatially CLEANER one.
- **Amended knee candidate: W_off=25 m, floor=0.10** — 8/8 env-2,
  best-on-surface env-2 GOSPA 13.38 (beats pmbm_land 17.74), phantoms
  strip-leaning (+10.45 tracks/scan vs today, mostly in the supervised
  near-land strip), far open-water field flat. Decision (user): revive at
  all, and if so which dial.

## 2026-07-12 — #24 assertion sweep: 214 triaged, 46 upgraded with teeth proofs, 2 design gaps exposed [suite health]

Ticket `2026-07-11-backlog24-assertion-sweep-ticket.md`; merged 164749f;
arbiter ceremony 1155/1155, 0 failed, 0 SKIPPED (inner-level fixtures).
Tests+docs only — production diff verified empty. Full record:
`docs/baselines/2026-07-11_b24_assertion_sweep.md` (+ inventory.json /
triage.txt). Highlights: 35 knife-edge + 66 vacuous of 214 metric-bearing
assertions; ~46 upgraded (banded floors, structural invariants, margined
adaptive comparisons, one-sided physical bounds); every upgrade
teeth-proven by mutation (EKF divergence trips accuracy gates 5.96→47.28;
NaN trips all 76 print-only guards; suppression-off trips harbor margins;
λ_birth=0 trips the birth ASSERT). W3 aq#1–5 dispositioned; aq#3 WORSE than
stated → b24-1 (PMBM k-best machinery has zero behavioral coverage);
b24-2 (T2T invariant-5 needs contributing-arm bench surface). Residual ~43
low-severity queued with recipe. Gaps ticket:
`2026-07-12-b24-gaps-ticket.md`.

## 2026-07-11 — Cl-4 endgame: floor-sweep price list (0.05–0.10) — NO KNEE in floor-space; spatial half still open [Cl-4]

Ticket `2026-07-11-cl4-endgame-cliff-reprice-ticket.md` (pre-amendment
scope: 1-D floor sweep); merged 1acfef2. Env-knob method (bench factory
only, unset = byte-identical). Write-up:
`docs/baselines/2026-07-11_cl4_cliff_price_list.md`.

- **No knee:** ≥6/8 env-2 revival needs floor ≤ 0.08 (philos +19.35 there);
  philos ≤ ~+12 needs ≥ ~0.093 (env-2 already 3/8). Graded trade, ~+5
  card_err per 0.01 of floor. Meaningful choice: **0.08** (8/8 channel,
  env-2 GOSPA 13.72 — beats pmbm_land's 17.74 — at philos +12.5 card_err /
  +10.7 GOSPA) vs **0.10** (philos clean, channel invisible).
- **Why (r_new = 0.1·(1−c)):** env-2 vessels cluster r_new ∈ [0.065,
  0.092] (≈15–42 m offshore); philos clutter is bimodal — median AT the
  shoreline (gated at every floor) with a tail overlapping the vessel band.
  Non-separability again, now in ramp-depth space.
- **No collateral, provably:** harbor (9.53/0.974) and env-1 (16.57)
  byte-identical at every floor (open-water/chart-free r_new = 0.1 never
  gated); pier phantoms untouched.
- **NOT yet measured (the amended ticket's other half, user's spatial
  split):** distance-from-shore distributions + the `offshore_halfwidth_m`
  × floor 2-D surface. The r_new data makes it promising: vessels sit
  ~15–42 m out, clutter median sits ON the shoreline — a narrowed strip
  (e.g. 25 m) may admit the vessels at full r_new while still gating the
  shoreline mass; the open question is how much of the clutter TAIL lives
  beyond the narrowed strip. Phantom MAP (distance of each re-admitted
  phantom) required per the user's operator-supervised framing.

## 2026-07-11 — Cl-4 Phase 2 Stage 0: vessel-past-structure gate FAILS (G1) — STOP-AND-REPORT; the revive-near-structure arc is EXHAUSTED [Cl-4]

Ticket `2026-07-11-cl4-phase2-floor-veto-build-ticket.md` Stage 0; merged
da8b778; NO Stage-1 tracker code written. Write-up:
`docs/baselines/2026-07-11_cl4_phase2_stage0_vessel_past_structure.md`.

- **G1 FAILS structurally:** a vessel transiting parallel to the pier
  inside the 25 m ramp has its floor-satisfying endpoint inside the flagged
  region for the whole pass → vetoed throughout. At the representative
  3 m/s / 30 m point, 5 seeds give latency {20 s, never ×4}; every in-ramp
  point is never or ≫15 s. The only pass (4 m/s at 50 m, bare-cell) is
  outside the ramp — vessel already clear of the structure. Margin box
  tightens it.
- **G2 PASSES** (pier stays vetoed with the vessel present, 5 seeds);
  no-pier baseline revives at +0 s — tool sound, failure real.
- **Root cause, now spanning the whole arc:** near a linear structure, a
  transiting vessel and the structure occupy the same signal space for
  every mechanism measured — sensor identity (A3: camera 80% structure),
  kinematics (1b/1c: association launders the walk into a CV transit), and
  now occupancy position (the veto that catches the laundered walk also
  catches the vessel). Phase 1d passed only because its fixtures kept
  vessels and structure spatially separate — the separation the Cl-4
  near-shore case doesn't have.

Endgame options (arbiter + user; NOT a tuning exercise): per-geography
residual / re-price the coverage cliff (with the ADR-0002 framing: the
zone's failure mode is an invisible real MOVING vessel — no hazard-channel
fallback for movers — which is the project's forbidden failure, vs phantoms
= the accepted degraded mode) / charted-extent identity signal (the one
signal not yet measured: pier-walk chains lie ON a charted line, a passing
vessel is laterally offset — needs charts as input and a lateral-offset
separability census vs radar σ).

## 2026-07-11 — Cl-4 Phase 1d: occupancy floor-veto = BUILD-ELIGIBLE (first affirmative of the arc; race won 11–27 s margin) [Cl-4]

Ticket `2026-07-11-cl4-phase1d-occupancy-veto-probe-ticket.md`; merged
de6464c. Offline `LiveOccupancyModel` (shipped, default params, unmodified)
as a veto on the Phase-1b floor: no revival when the chain-endpoint cell is
flagged persistent structure. Write-up:
`docs/baselines/2026-07-11_cl4_phase1d_occveto_probe.md`.

- **K3 (pier) PASS:** structure flags in 1–3 s (2–3 hits at α 0.3); pier
  chains satisfy the floor at 14–30 s → veto wins every race, Tier A chains
  AND Tier B real PMBM tracks (incl. the Phase-1c 104 m laundered walks),
  all 5 seeds, D=50 and D=70; zero revived. Margin box (bar ±0.15, 2× cell):
  0 revived at every corner. Sea clutter and anchored boats never classify
  as structure.
- **K1 (env-2) PASS, better than hoped:** 16/16 revived at +0 s latency.
  Mechanism = the shipped extent gate (`extended_cells_min = 4`): a compact
  dwelling vessel paints persistent cells but never a ≥4-connected
  component, so it is never "structure"; when it moves (the only way to
  satisfy D) its endpoint is a fresh cell. Holds even at bar 0.35.
- **K2 (philos) PASS:** veto monotone, inert on philos (= no-veto counts).

**The one gate for Phase 2 (implementer-flagged, arbiter-adopted):** no
fixture exercises a vessel transiting within the 25 m ramp of extended
structure — env-2's shore is a polygon (no dense returns), harbor's R6 boat
is stationary. The veto's K1 pass is therefore inert-by-data on env-2, not
vessel-vs-adjacent-structure discrimination. Phase 2 Stage 0 must measure a
moving vessel passing the pier (transient-veto latency ≤ 15 s) BEFORE any
build; HAXR real shore returns are the optional corroboration arm.

## 2026-07-11 — Cl-4 Phase 1c: smoothness + honest-association displacement = NO-BUILD confirmed & hardened (kinematic keying closed) [Cl-4]

Ticket `2026-07-11-cl4-phase1c-smoothness-probe-ticket.md`; merged e676d67.
Write-up: `docs/baselines/2026-07-11_cl4_phase1c_smoothness_probe.md`.

- **Hook 2 backfired:** the greedy-NN chainer UNDER-estimated the pier walk.
  Harbor pier max net displacement across 5 seeds: NN 84 m → motion-model
  chaining (Tier A) 130 m → real PMBM tracks (Tier B) 104 m. Motion
  consistency *sustains* the walk (steady apparent velocity along the 120 m
  linear pier predicts the next point and locks on). The D-only window
  closes further (env-2 targets reach 69–95 m per 30 s).
- **Hook 1 was apples-to-oranges:** on the same footing (both as chains),
  env-2 vessel chains max-step med/p95 = 13.8/19.2 m/s vs pier chains
  14.7/19.1 — identical. No per-step cap admits vessels while rejecting the
  pier. (Phase 1b had compared vessel TRUTH steps vs pier CHAIN steps.)
- **Verdict:** K1 fine (8/8), K2 never binds, K3 fails under both honest
  tiers, all 5 seeds, no margin. Root cause, now a named durable fact: **a
  chain along a linear extended structure is kinematically a constant-
  velocity vessel transit** — association (NN, motion-model, or the real
  PMBM) launders the pier walk into vessel-like motion. The conditional
  floor cannot key on suppressed-birth kinematics, in any measured form.
- **Scope caveat (sim-first honesty):** the walking-pier effect is measured
  on the synthetic pier (13 points / 10 m spacing / P_D 0.9). On the real
  near-shore structure we have (philos, within its ~1 km radar reach) the
  structure chains were STATIONARY (median net disp 0, Phase 1b) — the walk
  needs sparse point returns + misses on a linear feature. Sim is the
  controlled gate per methodology, but the trap's real-world incidence is
  unmeasured (no real pier-walk observed in our data to date).

Takeaway: path (b) closed in every kinematic form. The orthogonal signal is
map/extent knowledge of structure (charted static prior, or the live
occupancy layer's persistent-cell grid as a floor-veto) — arbiter decision
pending between that probe, path (c) re-pricing, and a documented
per-geography residual.

## 2026-07-11 — Cl-4 Phase 1b: conditional coverage floor (M,N,D rule) = NO-BUILD (env-2 revival and pier-walk overlap in net displacement) [Cl-4]

Ticket `2026-07-11-cl4-phase1b-coverage-floor-probe-ticket.md`; merged
d5e68e8. Chain census (`cl4_a3_census --mode chain/target`), zero shipped
behavior change. Write-up: `docs/baselines/2026-07-11_cl4_phase1b_floor_probe.md`.

- **K1 (env-2 revival):** easy — all 8 shore-huggers in-band 100%, net
  143–294 m, ≥69 m within any 30 s window, smooth (per-step p95 ≤ 7.9 m/s).
  Feasible only for D ≤ 72.6 m.
- **K2 (philos guard):** passes, NOT binding — in-band radar is dominated by
  stationary structure; at (M≥8, D≥50) only 2 moving chains = 0.2% of the A1
  residual (~+0.05 card_err vs the +10 budget).
- **K3 (harbor pier): THE binding gate.** The pier's 120 m extent lets
  greedy NN chaining (r_chain 25 m) walk its 10 m-spaced points to ~84 m net
  displacement on some seeds → robust exclusion needs D > 84 m. Empty
  feasible set: an extended structure walked by association mimics a transit
  in exactly the quantity the rule keys on.

Two measured escape hatches (NOT decided in the probe): (1) smoothness —
pier walks are jumpy (max step 16–20 m/s, teleporting between points on
missed detections) vs vessels ≤ 8 m/s: a per-step-speed term separates
cleanly with ~2× margin, but changes the rule family and philos smoothness
is unmeasured; (2) the NN chainer is a CONSERVATIVE proxy for K3 — at
r_chain 15 m the pier walk peaks at 50.6 m (< the 72.6 K1 ceiling), and a
real PMBM Bernoulli under a motion model resists teleports, so true pier
displacement is likely smaller. Scope unchanged: a displacement floor never
revives stationary near-shore vessels (static-hazard channel per ADR 0002).

Takeaway: Phase 1c commissioned — smoothness term + real-association
displacement measured together under binding criteria with robustness
margins (the #24 knife-edge lesson); paths (c)/per-geography-residual stay
the fallbacks.

## 2026-07-11 — Cl-4 Phase 1: A3 sensor-aware suppression = NO-BUILD (binding kill-criteria; guard unscoreable cross-workload) [Cl-4]

Ticket `2026-07-11-cl4-phase1-a3-probe-ticket.md`; merged 93c31ec. Offline
evidence census (`tools/cl4_a3_census.cpp`, research-only target), zero
shipped behavior change. Full write-up:
`docs/baselines/2026-07-11_cl4_phase1_a3_probe.md`.

- **Revival side (env-2) is real:** coverage_land = ZERO tracks on all 4
  scenarios (pure birth suppression — pmbm_land tracks them); both targets
  in-band 100% of scans with clutter-free evidence on hundreds of scans
  (lidar 35–63%, camera up to 100%). K1 PASS for camera/lidar variants.
- **Guard side fails structurally:** philos (the designated guard) carries
  NO lidar and NO camera on the bench path; the one labelled camera clip
  (sunset_cruise) points 0–10° off the bow while the shore clutter sits at
  +95°/+198° — time overlap, no bearing overlap. Camera/lidar variants are
  unscoreable on the guard workload.
- **Camera measured as a clutter source near shore:** on env-2 (the only
  camera workload), 79–85% of in-band camera bearings are off-target
  (structure), robust to doubling the gate. A camera-typed exemption
  re-admits ~80% clutter — the ADR 0001 §A3 warning, quantified. Lidar is
  clean (<21%) but Trondheim-only.
- **Verdict per binding criteria:** AIS-only passes K2 but fails K1 (0
  AIS in the deployment-relevant no-AIS condition); camera/lidar variants
  pass K1 but K2 is uncertifiable. NO variant builds. Root cause = the
  revival sensors and the guard workload share no clutter-free sensor —
  a data limitation of the gauntlet, not a tuning shortfall.

Takeaway: pivot Cl-4 to ranked path (b), the conditional coverage floor
(re-detection-based) — no cross-workload sensor dependency, and harbor's
pier becomes a scoreable guard. Durable facts: near-shore camera use must
be corroboration-gated, never a standalone exemption; A3-via-lidar worth
revisiting only on a lidar-equipped deployment+workload pair.

## 2026-07-10 — Harbor truth-sort reconciliation: card_err +11.64 is REAL (uncharted-pier phantoms), not fragmentation [Cl-3 integrity / Cl-4 input]

Ticket `2026-07-10-harbor-truthsort-reconcile-ticket.md`; merged ad5781e. The
ticket's premise (corrected yardstick "should read ≈0") was INVERTED — the
arbiter's 2026-07-02 record carried a wrong expectation. Measured:

- **Inventory:** the old `pmbm-harbor-truth-sort-fix` content is FULLY on master
  (3ee491f + 3aa9c58, both ancestors of the dossier base d94471e); all three
  additive-builder paths + HAXR replay sort; the no-fragmentation contract test
  (`HarborCompleteTruth.TruthIsTimeSortedIntoFortyCompleteGroups`) is compiled
  and green. Nothing missing.
- **Direct measurement:** harbor truth is clean — 5 objects × 40 samples, single
  monotonic run each, 200 samples → exactly 40 complete `{1..5}` groups. Zero
  fragmentation.
- **Resolution:** today's harbor baseline is byte-identical to the 2026-07-02
  corrected numbers (card_err 11.64, gospa_false 2362, lifetime 0.974). The fix
  moved 13.32→11.64, never toward 0. The +11.64 = ~11–12 phantom confirmed
  tracks on the uncharted 13-point pier (+ transient sea clutter); real targets
  ARE tracked (gospa_missed 34, lifetime 0.974). Three structural confirmations:
  pier geometry (13 points ≈ the excess), charted-pier A/B (11.64→7.43), and
  coverage_land (11.1→8.0).
- **What was actually wrong:** the promotion dossier's §1d caveat ("unmerged
  branch", "fragmentation artifact") — corrected in place, dated, with pointer to
  `docs/baselines/2026-07-10_harbor_truthsort_reconcile.md`.

Takeaway: the harbor yardstick is trustworthy; both delta AND absolute are
meaningful; driving the absolute down is exactly the Cl-4 objective (the phantom
source is the same uncharted structure the <50 m no-birth zone / sensor-aware
suppression must handle). Zero code changes; docs only.
## 2026-07-11 — T2T Checkpoint 2: shared-AIS double-counting gate (CI vs naive) [Cl-3, new capability]

`navtracker_t2t` M3 measured gate. Two trackers that both fuse the SAME AIS have
correlated errors; naive (independence-assuming) fusion double-counts it and goes
overconfident, covariance intersection (CI) does not. Base scenario `sim_ms_headon`
s0, per-arm tracker `imm_cv_ct_mht`, maximal sharing (both arms AIS-only). Full
write-up + interpretation: `docs/baselines/2026-07-11_t2t_gates.md`.

Position NEES (2-DoF, consistent ≈ 2), by test-local AIS σ (the loader's 30 m
pessimistic default is ~150× too loose for this near-perfect-AIS sim, so the arms
are under-confident at default — calibration is a harness-only lever, no generator
/ fixture / shared-loader change):

| AIS σ | role | per-arm NEES | CI mean | CI band | naive mean | CI cov95 | naive cov95 | naive/CI |
|---|---|---|---|---|---|---|---|---|
| 30 m | operational (real, stale AIS) | 0.42 | 0.48 | [1.87,2.13] | 0.83 | 1.00 | 0.984 | 1.73× |
| 16 m | coverage-calibrated (cleanest exhibit) | 1.32 | 1.33 | [1.87,2.13] | 2.66 | 0.95 | 0.82 | 2.00× |
| 12 m | NEES≈2 calibrated (demo row) | 2.06 | 2.08 in-band | [1.87,2.14] | 3.16 breaches | 0.90 | 0.83 | 1.52× |

**Formal gate (arbiter ruling 2026-07-11): the ROBUST invariants** — naive/CI mean
ratio > 1.4× at every σ AND the monotone coverage gap (naive cov95 < CI cov95).
σ=16 is the cleanest exhibit (CI 0.95 vs naive 0.82 at 2.0×). σ=12 stays a
demonstration row only (satisfies the literal "per-arm NEES≈2 → naive out of band,
CI in" recipe) but the mean-band is knife-edge in σ (fused NEES is heavy-tailed:
median ≈ 0.5 ≪ mean ≈ 2), so the claim must NOT hang on it — #24 applied to our
own gate. σ=30 is the operational-context row.

**Engine note (combined-review fix, `4287459`):** the fused delete-clock now
counts idle from the last REPORT, not the last coasted contribution. This shifted
ONLY the σ=30 maximal row (naive 0.824→0.833, ratio 1.71→1.73×); all calibrated
rows byte-identical. Two review rounds fixed: per-cycle M-of-N over-counting,
birth-window growth, coast-clear, delete-clock; plus 3 vacuous-assertion hardenings.

Reproduce (worktree `../navtracker-t2t`, foxglove off, fixtures at main tree):
```
cmake --build build -j --target navtracker_tests
SIMMS_DIR=/home/andreas/workspace/navtracker/tests/fixtures/sim_multisensor \
  ./build/navtracker_tests --gtest_filter='T2tScenarioRun.*'
# the calibrated sweep + band-violation gate:
SIMMS_DIR=... ./build/navtracker_tests \
  --gtest_filter='T2tScenarioRun.PerArmNeesCalibrationAndBandViolationGate'
```
Determinism: fused output byte-identical on replay
(`T2tScenarioRun.FusedOutputIsDeterministic`). Checkpoint 2 ACCEPTED; GO for M4.

**M4 robustness scenarios (same date, `sim_ms_headon`/`sim_ms_crossing` s0):**
- **4 `t2t_dropout`:** B silent 60 s → **zero** added fused-id churn vs no-drop
  baseline (both 8 distinct ids, all inherited per-arm CPA churn), id spans the
  dropout, cov inflates (radar-only trace 1.97e5 vs 1.75e3 fused) then recovers.
  Latency (B 2 s late): reports ACCEPTED (per-source monotonic), fuser predicts
  to latest ts and fuses → bounded lag (GOSPA 25.2 vs 24.4), no id churn.
- **5 `t2t_conflict`** (B +150 m, claims 5 m σ): CI gospa 29.88 ≈ naive 29.89,
  but naive NEES 3.86 > CI 3.38 — CI limits overconfidence, not the bias →
  seeds the input-de-weighting ways-to-improve entry. Characterization, no gate.
- **6 `t2t_cross`** MMSI A/B: churn-dominated, within noise (id_switches 13 vs
  11.7) → report-only (#24). Clean penalty value shown in the controlled
  associator A/B (`T2tAssociator.MmsiConflictPenaltyBreaksKinematicTieToCorrectPairing`);
  invariant 5 held (both targets fused despite MMSI).
- Full-stack `tests/integration/test_t2t_full_stack.cpp` + `app/example_t2t.cpp`
  (two live Trackers → NavtrackerSource → fuser). Rows in the gates doc.
  Reproduce: `--gtest_filter='T2tScenarioRun.*:T2tFullStack.*'`.

## 2026-07-09 — Backlog #25 Phase 2b Stage 2: BUILT the velocity-runaway guard (deweight @ 400 m) [Cl-3]

On arbiter GO. Built the update-acceptance position-innovation guard in
`PmbmTracker` (per-instance, ctor-threaded, default OFF; kinematic-only —
existence/mass/birth/id untouched). Full write-up:
`docs/baselines/2026-07-09_b25_phase2b_stage2.md`; reference
`docs/algorithms/velocity-runaway-innovation-gate.md`; learning
`docs/learning/11-gating-gnn-hungarian.md` §"A second gate" (+ figure
`11-innovation-gate.png`).

**Rider 1 (pick the treatment by measurement).** A/B reset vs deweight × D200/D400
on the 6 dying cases, gate = loss-seconds-overlapping-CPA + re-acquire-id count:

| variant | CPA-overlap loss (s) | dying loss (s) | reacq ids | idsw all/dense |
|---|---|---|---|---|
| OFF | 163 | 1366 | 45 | 34/30 |
| reset 200 | 51 | 630 | 9 | 13/12 |
| reset 400 | 299 | 550 | 14 | 17/13 |
| deweight 200 | 179 | 939 | 17 | 9/8 |
| **deweight 400** | **6** | **544** | 10 | 15/11 |

**Winner: deweight @ 400 m** — CPA-overlap loss 163 → **6 s** (Q2b blackouts
eliminated; per-case ≤3 s). Reset *stalls* the track (velocity→0 while the target
moves) so it stays lost; deweight keeps it moving with a wide velocity prior and
re-locks. Shipped as `imm_cv_ct_pmbm_coverage_land_ivgate` (library default OFF).

**Rider 2 (id-switch watch-item).** id-switches ON vs OFF: every variant REDUCES
them (34/30 → 15/11 for the winner) — **no swap regression**; the neighbour-snap
risk is real in principle (parked coalescence guard) but doesn't materialise.

**Rider 3 (band + phantom bonus).** D400 is the clean band (D200 marginal). The
82.5 % clutter-born phantom majority is **presence-neutral** (−125 confirm,
survivors longer, total track-seconds ≈ 0) — not a phantom killer; the band is
decided by CPA-overlap, not the bonus.

**No-regression.** deweight@400 ON vs OFF: **philos KEEP byte-identical (0/8),
AutoFerry byte-identical (0/72)** — the guard never fires on real data (0 % false-
fire, honest innovations < 400 m); sim_ms net-beneficial (headon/overtaking/
ais_dropout improve; crossing ospa +8 within synthetic noise). Kinematic-only ⇒
miss-P_D brake + λ_C/birth invariant untouched by construction. Guard OFF is
byte-identical to the pre-guard binary; the coverage_land knob extraction into
`makeCoverageLandPmbmConfig()` is a proven no-op.

Suite 1089 ran / 1081 passed / 0 failed / 8 skipped (HAXR/RBAD/Boston data-gated,
named; sunset-6c ran+passed on this toolchain). `Config.DefaultConfigsHaveUnique
Labels` → 38 (+`…_ivgate`). Placement/escalation unchanged from Stage 1 (CT-mode-
keyed estimator clamp is the parked escalation; not needed on any workload here).

## 2026-07-09 — Backlog #25 Phase 2b Stage 1: true-innovation re-probe (CHECKPOINT) [Cl-3 diagnostic]

Extended the `IPmbmDiagnosticSink` surface (additive, default-off, byte-
identical) with the TRUE applied-measurement position innovation (measurement
ENU − predicted ENU + norm) and the per-mode IMM weights, then re-ran the
Phase-2a D-axis probe on the real innovation. Full write-up:
`docs/baselines/2026-07-09_b25_phase2b.md`. **No behavior code — checkpoint.**

**Byte-identical proof.** sim_ms states.csv diag ON==OFF; all 46 states.csv
(22 imazu+6 sim_ms+18 autoferry) my diag-ON == the pre-2b binary (update-path
edit inert); 260 non-timing metric rows ON==OFF; diag re-run deterministic. The
`enumerateChildren` innovation capture is sink-gated → zero work / byte-identical
when no sink.

**Binding re-probe (true innovation).** Detection: 5/6 dying flagged before
permanent gate-exit at every D_max (6th = the imazu_22 id7 coalescence, no clean
exit). False-fire (autoferry_unanch+sim_ms): D100 3.39%/1.09% FAIL, **D200
0.70%/0.22% PASS, D400 0.06%/0.02% PASS** (detection-surface / all-rows). REAL
autoferry = 0.00% at every D. **The true innovation reproduces the Phase-2a
proxy verdict — position-innovation gate PASSES at D_max 200–400 m.**

**Placement (the question the proxy could not answer).** The runaway is
two-phase: a SEQUENCE of moderate innovations (50–108 m, each < D_max) under IMM
**CT (turn) mode** dominance pumps speed 2→110+ m/s over ~25 s (the track grabs
returns near its increasingly-fast prediction, so innovation stays small), THEN
a single OVERSIZED accepted innovation (imazu_15 id6: 484 m at t=355) lands as
the gross mis-association. Max innovation before the first >200 m flag: 108/158/
173 m across the three traced tracks. So: the clean, binding-passing TRIGGER is
at **update-acceptance** (the oversized innovation; ~0 false-fire), but the
velocity is already elevated when it fires — a bare "reject/coast" action would
flag-but-not-fix; the evidence favours **accept-position + reset/deweight-
velocity**. The moderate build-up is estimator-internal (CT-mode update too
aggressive) — an estimator clamp is the fallback but must key on CT-mode/
velocity-change, not innovation magnitude (magnitude clamping the build-up
re-introduces the Phase-2a velocity-signal false-fire). IMM finding (closes the
2a (c) gap): CT-mode dominance + violent 0↔1 mode thrash is the divergence
signature; healthy scans are CV-dominant (0.9+).

**Stage-1 verdict: PASS → recommend Stage 2 builds the gate at update-acceptance,
`innov_gate_max_m` ∈ 200–400 m (per-instance, default OFF), action = accept-
position-reset-velocity, kinematic path only (existence/birth untouched — the
philos brake + ADR-0002 stay untouched by construction). Awaiting arbiter go.**
Suite 1089 ran / 1081 passed / 0 failed / 8 skipped (HAXR/RBAD/Boston data-gated,
named; sunset-6c ran and passed on this toolchain as in 2a).
## 2026-07-09 — Anchored-vessel corroboration veto ISOLATED: real + protective on HAXR (verdict a); default unchanged [Cl-3 corroboration seam / Stage-1b closeout]

**What.** Gave the always-on occupancy corroboration veto (never suppress a birth
within `veto_radius_m` of a recent AIS/cooperative fix) a per-instance A/B partner
`LiveOccupancyParams::corroboration_veto_enabled` (default `true`), then measured
its ISOLATED effect holding the AIS arm ON in both arms — the increment-8
entanglement (AIS turned the veto on AND changed fusion input at once) that left
its benefit "unmeasurable". Toggle-only; zero default/behaviour change. Branch
`veto-isolation-ab` (base `317ecfd`). Full doc + tables:
`docs/baselines/2026-07-09_veto_isolation.md`.

**Byte-identical (default flag).** `kattwyk_08` coverage config (AIS fed → veto
path fires) + philos sunset occupancy tests, reverted-317ecfd build vs toggle
build: all 811 HAXR metric rows identical, philos hazard diagnostics identical.
Plus the fixed-input invariant test
`LiveOccupancyModel.CorroborationVetoToggleDefaultOnReproducesVetoOffFallsThrough`
(ON → suppression exactly 0 at a fix; OFF → the same hazard ramp as no-fix →
suppression only rises, never orphans a birth: ADR-0002 conservation holds both
ways).

**HAXR 3-site A/B** (kattwyk/parkhafen/seemannshöft_08, dec50 eps=50, common 285 s
window, `imm_cv_ct_pmbm_occupancy_detector_coverage`, AIS ON both arms, veto
toggled). occ_suppress_hits OFF→ON: kattwyk 45848→39417 (**−14.0%**), parkhafen
24578→13599 (**−44.7%**), seemannshöft 104810→69631 (**−33.6%**). The lift
recovers missed tracks (card_err_mean toward 0 on all three — seemannshöft
−1.59→−0.96; gospa_missed down; lifetime up) at the cost of more false tracks near
the lifted regions (gospa_false up, seemannshöft +123), so net gospa_mean is
~flat (kattwyk/parkhafen) to slightly worse (seemannshöft +0.47).
`occ_peak_structures` unchanged both arms → clean isolation (the veto changes
whether a birth is suppressed, not what is learned as structure).

**Sim** (`sim_ms_anchored_camera`, perfect truth, `imm_cv_ct_pmbm_occupancy_detector`):
INERT — every metric byte-identical ON vs OFF, `occ_peak_structures=occ_suppress_hits=0`
both arms. The layer is fed but forms no structure in open water (the anchored
vessel is tracked → low clutter-weight into the feed → never suppressible
structure); nothing to veto. The perfect-truth protective demo is carried by the
fixed-input unit test, not this scenario. Reported honestly.

**Verdict (a): real and protective — keep ON (default unchanged).** The isolated
effect is large and directly attributable (14–45 % suppression lifted near known
vessels) and protective in the ADR-0002 sense (fewer missed, better continuity).
The trade for the arbiter: on fixed-shore dense-harbor sites the lift also admits
phantoms within `veto_radius_m` of a fix (net gospa flat-to-slightly-worse there);
the lever if that cost matters is tightening `veto_radius_m`, NOT disabling the
veto — an arbiter/user call, not changed here.

**Commands.** `ctest --test-dir build -R VetoIsolationHaxrAB` (~6.5 min, local HAXR
fixtures), `-R VetoIsolationSimAB` (SIMMS fixtures), `-R CorroborationVetoToggle`.
Fixture md5s in the baseline doc. Full suite green; skips named in the handoff.

## 2026-07-08 — Backlog #25 Phase 2a: runaway census + offline velocity/innovation-bound probe [Cl-3 diagnostic]

Offline probe (no build; new read-only `tools/pmbm_phase2a_probe.py` over the
Phase-1 diag export). Config `imm_cv_ct_pmbm_coverage_land`, seed 0; 22 Imazu +
6 sim_ms (census) + 18 AutoFerry (false-fire). Full write-up:
`docs/baselines/2026-07-09_b25_phase2a_probe.md`.

**Question A — census.** 19 869 Confirmed rows > 50 m/s. **82.5 % are
clutter-born short-lived phantoms** (930 tracks, median life 117 s) vs 17.5 %
target-born (46 tracks, median 717 s). In single-target `imazu_01–04`, **99.5 %**
of runaway rows are clutter-born. → Phase-1's "systemic IMM defect" gloss
*shrinks*: the single-target runaway is phantoms, not the target track. But the
CPA-**dying** tracks are genuinely target-born long-lived (imazu_15 id6 595 s,
id7 718 s) — H3-at-the-CPA stands. Contest is 3 % in aggregate, concentrated at
dense CPAs (imazu_21 137). (c) IMM mode not exported — declared gap.

**Question B — bound probe (V∈{25,50,75} m/s, D∈{100,200,400} m).** Axis
separation is decisive:
- **SPEED bound FAILS** the false-fire kill-criterion: 6.6–11.4 % on sim_ms,
  2.2–4.4 % on imazu single-target, **0 %** on AutoFerry. The sim_ms false-fires
  are *well-positioned* healthy tracks (median 22–31 m, min 1.2 m from truth)
  carrying transient velocity-**state** spikes of 159–235 m/s during crossing/
  head-on ambiguity.
- **JUMP / position-displacement bound PASSES** at D ≥ 200 m: 5/6 dying tracks
  flagged before permanent gate-exit, false-fire **0.13 %** (sim_ms), **0.00 %**
  (AutoFerry + imazu single-target). The position stays put for a
  measurement-corrected healthy track even when the velocity state overshoots.

**Verdict: BUILD the position-innovation gate (NOT the velocity bound), band
D_max ≈ 200–400 m, guard at the estimator update / association gate — clamp/reject
kinematics, never delete the Bernoulli** (keeps the miss-P_D existence brake and
ADR-0002 untouched; the 82.5 % clutter-phantom majority makes it a clutter-killer
bonus). Two Phase-2b pre-conditions: (1) the true measurement-innovation is not
exported — the D-axis is a posterior-position-jump proxy; add one additive
default-off field and re-probe to choose estimator-clamp vs association-gate;
(2) pair with a coalescence guard — per-truth margins are confounded by
close-pass id migration across near truths (imazu_15 id6 migrates 152/153→151;
imazu_22 id7 covers 2 truths). Alternates ranked: (1) position-innovation gate,
(2) coalescence guard, (3) ambiguity-gated soft update (PDA branch, OFF today,
restrict to contested close-pass). Zero core/config change; determinism
re-verified byte-identical.

*Verification (branch `backlog25-phase2a`, off master `afc47d2`): the full
gtest binary run from the worktree root (philos/autoferry symlinked, SIMMS_DIR →
main tree) = **1089 ran, 1081 passed, 0 FAILED, 8 skipped**. The 8 skips are all
HAXR / RBAD / Boston-coastline data-gated (fixtures absent here): GeoJsonCoastline.
BostonFixtureSmoke, HaxrOspa.KattwykHourEkfGnnBaseline, LosShadowGuard.
SimAnchoredControlGuardInert, ReplayScenarioRun.HaxrScenarioCarriesDatum…,
RbadScenarioRun.{Generate…,MhtConsistency…,DeterministicReplay}, LosGuardHaxrAB.
GuardIsNearInertOnFixedShoreStation. NOTE for the sunset6c-assertions ticket: the
3 `PhilosCoverageDecay6c.Sunset*` assertions this eval-log documents as red on
master (below) **RAN and PASSED here** (isolated and in-suite; test file
byte-identical to master, no core change) — the `#24` knife-edge
`EXPECT_GT(cov_astern, uni_astern)` lands green on this toolchain (g++13 Release,
current fixtures). Consistent with the #24 FP-fragility finding; it does not
change the disposition that those assertions must be replaced. Caveat on
plain `ctest`: it runs each case from the build dir, so the philos-fixture-gated
6c cases GTEST_SKIP there — `100% tests passed` under `ctest` alone would be a
false green; the numbers above are from running the binary at the worktree root.*

## 2026-07-08 (correction) — master IS red on 3 sunset 6c tests since f11d6e7; the "concurrent-mutation artifact" attribution was WRONG for them [suite health]

**Finding (two independent isolated worktrees, deterministic, serial-run
confirmed).** `PhilosCoverageDecay6c.Sunset{CoverageAwareHoldsStructureAndProtectsUnsweptCells,
CameraObservedEmptyFlagsVacatedCells,CameraEvictionRemovesDepartedPinsHoldsChartStructure}`
fail on clean master (`7f5cd17`, and `3ae355f` = +additive diag hook):
reproduced by the Cl-1 implementer (3 clean runs) AND by the arbiter's
verify-b25 worktree, including a **serial 3-test-only run** — NOT
load-dependent, NOT concurrency. Failing assertion is the backlog **#24
knife-edge case (2)** verbatim: with the LOS shadow guard ON
(`occupancy_detector_coverage`), guard-held mass shifts the clutter-adaptive
bar and `astern_blob` de-emits under the coverage config →
`cov_astern > uni_astern` fails (0 vs 13).

**How it was masked (attribution correction).** `f11d6e7`'s commit message
attributes the earlier red to a "concurrent-mutation artifact". That was true
for the 55-failure incident itself, but it HID a genuine 3-test breakage:
(a) the post-revert verification ran with the guard reverted → tests passed;
(b) the re-land verification's worktree did not have these fixture-gated
tests running (skip = counted as pass); (c) the isolated 6c 5/5 pass cited
at the Imazu merge ran during the revert window. Lesson recorded: an
isolated-worktree verification must ALSO diff its skip list against the
expected-skip set — `100% tests passed` proves nothing about tests that
silently skipped.

**Disposition.** The guard stays (net-beneficial, merged deliberately); the
three A/B assertions are the defect — they pin the epsilon-fragile
cross-config flip that #24 rules invalid, exactly what `c0ac493` already
fixed for the loiterer assertion. Fix ticket:
`docs/superpowers/plans/2026-07-08-sunset6c-assertions-ticket.md`.

## 2026-07-08 (resolution) — master-red RESOLVED by assertion upgrade only; zero behavior/config diff (branch `sunset6c-assertions`) [suite health]

**Outcome.** The three `PhilosCoverageDecay6c.Sunset*` reds above are fixed by
re-expressing the fragile assertions per #24 + the `c0ac493` precedent. NO
change to the guard, `LiveOccupancyModel`, or any config — tests only. Full
suite green in an isolated worktree; the three tests RAN (not skipped) green,
plus a serial 3-test-only run green (63.2 s). Build off base `e86d2fc`.

**Root cause confirmed = #24 flip, NOT a behavior break.** Two phenomena, both
adaptive-bar fragility, drove all five failing assertions:
- **(A) `astern_blob` de-emits under the coverage config** (universal=13 /
  coverage=0). The clutter-adaptive bar (median × factor) is non-monotone in
  persistence, so the guard-held mass shifts the bar and the marginal
  `midriver_grp`↔`astern_blob` region flips its emission class. This is the
  SAME invalid cross-config invariant that check (2) in the sunset test was
  already removed for (2026-07-07).
- **(B) the ferry berth pin decays before its post-vacate empty window.** The
  eviction A/B proves it: `ferry_v1_a before/after t98 = 113/0` in BOTH arms —
  0 emitted hazards after the ferry vacates. So the emitted-hazard `camera_empty`
  flag (`countCam`) is 0 and there is no post-move phantom to evict. Same
  membership-hysteresis fragility the eval-log already flagged for the loiterer,
  now reaching the ferry.

**The mechanisms are ALIVE (this is why it is an assertion fix, not a behavior
finding).** Config-independent camera-empty CELL streaks matured on
`ferry_v1_a`=**41** scans and `loiterer_v2`=**203** scans (244 total across the
two departed vessels); `astern_blob`=**0** (correctly — out of centre FOV).
Eviction still removes mass (total hazard-scans off=6128 → on=5912). The
emitted-hazard flag path is the only thing that went to ~0 (13 flags map-wide,
none on a named region) — precisely the adaptive-bar-fragile signal #24 says not
to pin.

**Per-test old → new assertion (why valid under #24):**

- **876 `SunsetCoverageAwareHoldsStructureAndProtectsUnsweptCells`** (was
  `test:274`). OLD: `EXPECT_GT(cov_astern, uni_astern)` — cross-config per-region
  A/B on a marginal region (#24 case 2, the invalid invariant already removed for
  check (2)). NEW: a SINGLE-RUN banded floor on the coverage arm alone — a hazard
  is emitted on ≥ 90 % of scans (measured 100 %: min hazards/scan = 1). Valid
  under #24 case 1: it is a robustly-banded aggregate of ONE run, not a
  difference between two feedback-coupled pipeline runs. The one-sided "guard
  only adds mass" invariant remains proven with fixed inputs in
  `LiveOccupancyModel.ShadowGuardOnlyAddsMassOnFixedInputs`.
- **879 `SunsetCameraObservedEmptyFlagsVacatedCells`** (was `test:502`). OLD:
  `EXPECT_GT(countCam(*ferry_a), 5)` — emitted-hazard `camera_empty` flag, which
  needs the berth pin to survive the adaptive bar into the empty window. NEW:
  `EXPECT_GT(streakMaturedScans(*ferry_a), 0)` — the config-independent
  camera-empty CELL streak (measured 41), the raw "camera proved this cell empty"
  fact, independent of the persistence bar. This is the `c0ac493` loiterer fix
  applied to the ferry. Check (4) likewise moved from `countCam(*astern)==0`
  (trivially 0 now that astern de-emits) to `streakMaturedScans(*astern)==0`
  (measured 0) — an absence assertion on the config-independent signal, which
  actually tests the FOV gate.
- **880 `SunsetCameraEvictionRemovesDepartedPinsHoldsChartStructure`** (was
  `test:616` and `:626`). OLD `:616`: `EXPECT_LT(ferry_on_pp.second,
  ferry_off_pp.second)` — pins a residual post-move phantom (0/0 now, decayed
  before the window). NEW: `EXPECT_LE(...)` — one-sided (eviction can only spend
  pins, never add), robust; the strict "eviction removes mass" claim is carried
  by the surviving aggregate (1) `haz_on < haz_off` (5912 < 6128). OLD `:626`:
  `EXPECT_GT(astern_on, 0)` — an emission existence pin on the #24-flipping
  region; DROPPED. The chart-held invariant is the surviving one-sided
  `EXPECT_GE(astern_on, astern_off)` (eviction never REDUCES charted structure);
  post-move eviction correctness is gated on the synthetic `EvictionScene*` per
  the circularity rule (this clip has no truth).

**Also corrected:** the file header's stale "presence is monotone ≥ universal /
never holds LESS presence than universal over any region" claim (already
falsified by the check-(2) removal) → replaced with the single-run retention
statement + pointer to the fixed-input unit invariant.

**Verification (isolated worktree `../navtracker-6cfix`, base `e86d2fc`):**
`ctest -j` → `100% tests passed, 0 tests failed out of 1090` in **221 s, with
ZERO skips** — every fixture-gated family was wired (generated
`sim_multisensor/imazu_*_s0` + `rbad/*` scenario dirs symlinked from the main
tree, the same shadowed-tracked-dir gap the philos fixtures had; `data`/`tests`
build symlinks for the cwd=build/ replay paths). The three formerly-red tests
RAN and passed (876/879/880), plus a serial 3-test-only run (`-j1`) green in
63.2 s. Skip-list diff (the new rule): expected env-gated set = ∅ here, actual
skips = ∅ — a bare `100% tests passed` is not trusted alone; the named
zero-skip result is what clears it. Commands + build base in the handoff.

## 2026-07-08 — Backlog #25 Phase 1: PMBM close-pass track loss is ESTIMATOR DIVERGENCE (H3), not miss-starvation (H1) [Cl-3 diagnostic]

**Localization pass — no fix, no config/algorithm change.** Answers backlog #25:
which stage kills the PMBM (`imm_cv_ct_pmbm_coverage_land`) track at the
sustained close passes where it drops a target for tens of seconds at the CPA
(Q2b, above). New code is diagnostic-only: an additive, default-off,
per-instance PMBM per-scan introspection sink (`core/pmbm/PmbmDiagnostics.hpp` +
`PmbmTracker::setDiagnosticSink`, guarded so null = byte-identical), a bench
recorder (`--export-pmbm-diag-dir`), and one Python reproducer
(`tools/pmbm_closepass_trace.py`). Full write-up + trace tables in
`docs/baselines/2026-07-08_b25_localization.md`. Ticket
`docs/superpowers/plans/2026-07-08-backlog25-localization-ticket.md`.

**Verdict — H3 (estimator state divergence) is the killer; H1 only a downstream
secondary effect; H2 absent.** The arbiter's H1 working hypothesis is
**refuted**: the target is lost because the Bernoulli tracking it has its
**velocity state run away** and leaves the 100 m match gate **while `r` is still
high** (0.99–1.0 at the instant it crosses out), not because existence starved.
Through the two worst losses (imazu_15 158 s, id 6; imazu_22 96 s, id 7 — both
overlapping the own-ship CPA): imazu_22 id 7 keeps r 0.98–1.0 the whole window at
speed 3,700–4,500 m/s; imazu_15 id 6 leaves the gate at t≈477 with r=1.0, speed
839 m/s, dist 1,838 m, then coasts off (→156 km) with r decaying 1.0→~0.5 only
*downstream* of the divergence (never reaching the 0.1 floor in-window). 5 of 6
traced dying tracks are pure H3; the one mixture (imazu_15 truth 153) diverges
then miss-starves at run-end. **H2 ruled out:** `hyp_dropped_floor =
hyp_dropped_cap = 0` across all windows (single K=1 hypothesis); r_min prunes
only already-sub-floor phantoms.

**Adversarially verified** (independent re-analysis of the raw diag CSVs):
causal claim upheld, with two refinements incorporated. (1) Velocity runaway is
a **systemic** IMM filter-stability defect, not CPA-unique — even single-target
imazu_01 has 439/959 (46 %) confirmed-track rows > 50 m/s (the same phantom
population as the +0.77 clutter over-count); the sustained pass is what steers
the divergence onto the *target's own* track and strips its measurement stream.
(2) A **neighbour-lock / measurement-hijack** data-association effect prolongs
the loss and delays re-acquisition (survivors bind to neighbour truths; the
diverged K=1 track keeps hijacking the abandoned target's returns, starving a
re-birth) — concurrent with H3, distinct from H1 existence-decay.

**Mechanism.** Wide gate (20) + K=1 winner-take-all hard-commit + sustained
proximity → after the track drifts in the ambiguity, re-grabbing the true return
dumps a large position innovation into velocity (high-cov overshoot); the IMM
CV/CT filter has no speed/innovation bound, so velocity → gate widens → admits
distant returns → runaway divergence. Severity scales with ambiguity duration:
control imazu_01 (isolated) tracks at the true ~2–3 m/s; imazu_08 (85 m) mild
(200–450 m/s, holds); only sustained proximity (15/22) diverges at the CPA.

**Byte-identical (acceptance #3).** Post-hook binary *with the diag sink active*
reproduces all 22 Imazu `states.csv` bit-for-bit vs the pre-hook binary; on the
32 `--with-simms` scenarios diag-off vs diag-on gives byte-identical states +
**1488/1488 accuracy-metric rows identical** (only the wall-clock
`scan_proc_ms_*` differ). Faithfulness anchor: every Confirmed states track is
contained in the diag (mass ≥ 0.5, pos err 0.000 m) on 100% of truth-scans
across 5 cases. Loss reproduces the Q2b counts exactly (no determinism alarm).

**Phase-2 conditioning (for the arbiter).** The killer is on the update/gating
path, not the misdetection existence recursion — so an estimator-robustness fix
(maritime speed/innovation gate; ambiguity-aware soft update vs hard
winner-take-all — the PDA soft branch exists but is OFF; or a coalescence guard)
is orthogonal to the miss-P_D existence brake that holds philos over-count down,
and cannot weaken it by construction, PROVIDED it fires only in the
association-ambiguity / large-innovation context and leaves the existence/birth
channel untouched (per-instance, default-byte-identical, re-measured on
philos/HAXR KEEP before promotion; PDA-soft must be gated to contested close-pass
scans — it regressed open-sea lifetime globally).

Full suite green in the `backlog25-localization` worktree: **100% tests passed,
0 tests failed out of 1090** (33 skipped = data/-gated replays only —
Philos/HAXR/AutoFerry/R-BAD/camera/GeoJSON; the Imazu battery RAN via
`SIMMS_DIR`→main-tree: `Imazu22ScenarioRun.*` all 5 Passed incl. the
fixture-gated `DeterministicReplaySampled`/`IdSwitchesCoarseBand`). States export
byte-deterministic.
Reproducer `tools/pmbm_closepass_trace.py` sha256 `7f0ba18c`; input fixtures =
the 2026-07-08 set in this log.

## 2026-07-08 — Backlog #11 Imazu churn diagnosis: conveyor (not swaps) + PMBM mirror + knob measurement [Cl-2/Cl-3 diagnostic]

**Diagnosis pass — no config/algorithm change.** Root-causes the Imazu identity
numbers from the 2026-07-08 battery (above). Only new code: three Python analysis
scripts (`tools/imazu_switch_forensics.py`, `tools/imazu_cardinality_timing.py`,
`tools/imazu_trackloss.py`) consuming the existing bench `--export-states-dir`
output; nothing under `core/`/`ports/`/`adapters/`/`app/` touched. Findings
independently re-derived by an adversarial verifier (from-scratch brute-force
optimal-assignment solver + own bench parser) — all five claims confirmed, no
classifier defect. Full write-up + tables in
`docs/baselines/2026-07-08_imazu22.md` (dated addendum). Ticket
`docs/superpowers/plans/2026-07-08-backlog11-imazu-churn-ticket.md`.

**Stop-and-report (acceptance #5) resolved NEGATIVE-for-stop:** the 2026-06-12
switch-forensics tool was a throwaway (never committed). It was *rebuildable
without any core change* — the existing `--export-states-dir`
(`scan,time_s,kind,id,east_m,north_m`, scenario-agnostic) carries everything, so
the method was re-implemented as Python that re-derives the bench's own per-scan
Hungarian assignment (`Metrics.cpp assignPerStep`, strict gate 100 m; JV port of
`Hungarian.cpp`) and continuity walk. **Faithfulness proven:** the script's
per-truth `id_switches`/`track_breaks` equal the bench's `*:truth_<id>` rows for
**all 22 cases** (MHT, PMBM, recapture) — the classification is an exact
decomposition of the reported metric, not a re-estimate.

**Q1 — MHT churn is the duplicate-track conveyor, not swaps.** Aggregated over
all 18 multi-target cases, duplicate-track churn = **88.9%** of id-switch events
and genuine pair-swaps **11.1%**; dup-churn is ≥76% on 17 of 18 cases (sole
exception imazu_08 at 65% dup / 35% swap; swap fraction ranges 0–35%).
Signature: **up to 81 distinct track ids for 3 truths** (imazu_20). Same
mechanism as sc5 2026-06-12 but a different trigger — sc5 was camera-bearing
over-confidence; Imazu carries no camera, so here it is **radar cross-range
ambiguity between targets passing inside the gate**. Geometry: churn + *all*
swaps concentrate on whichever pair passes within radar ambiguity (imazu_17/20:
T1↔T2 co-course overtakers at 28.2 m carry all swaps, isolated crosser T3 has 0;
imazu_14: the two crossers at 10.9 m). Position holds (RMSE 25–28 m) throughout.
break+re-confirm is a real secondary channel (≈ half of breaks re-confirm a new
id on churny cases).

**Q2 — PMBM's +0.77 over-count is clutter birth noise, NOT the swap mirror.**
Cardinality decomposed into extra(over)/missed(under): the ≈ +0.77 over-count is
**present unchanged on a single isolated target with no crossing** (imazu_01:
mean tracks 1.766, extra 0.786, misses ≈ 0; 39 distinct Bernoulli ids for 1
truth, 0 id-switches) — crossing-independent over-birth (λ_C 2e-8, ≈ 4
clutter/scan).

**Q2b — PMBM's real close-pass failure mode is losing the track (elevated per
arbiter).** `tools/imazu_trackloss.py` finds per-truth loss windows (= breaks),
their duration, before→after id, and CPA-window overlap (own-ship + truth-truth,
own-ship from fixture `ownship.csv`). The six densest cases (14/15/17/19/20/22 —
exactly those whose headline lifetime drops to 0.67–0.81) drop the ambiguous
target for **tens of seconds**, at/around the CPA: substantial (≥10 s) losses of
62–158 s, 398–709 s total unassigned time per case, **6–27 losses re-acquiring
under a NEW id**, a handful permanent (never re-acquired), and the longest losses
overlap the **own-ship** CPA (imazu_15 158 s, imazu_22 96 s — the collision-
relevant moment). Controls confirm it is proximity-driven, not baseline:
single-target and the 85 m pass (imazu_08) show only 1–4 s flicker, 0 substantial
losses, 0 CPA overlap. Caveat: closeness is necessary but not sufficient
(imazu_12's 0.6 m fleeting pass keeps identity, lifetime 0.96) — the driver is
*sustained* co-course proximity, matching Q1. So MHT and PMBM express the same
ambiguity oppositely and both hurt at the CPA: MHT holds the track and churns
identity; PMBM holds its primary id but drops the target (often re-acquiring a
new id).

**Q3 — #11 knobs on Imazu (measurement only, no promotion):**
`share_ambiguous_bearings` = structural no-op (no bearings on Imazu);
per-sensor `gate_threshold` = not `--config-eq`-reachable, enabling it is a
forbidden config edit (prior 2026-06-12 global-gate sweep already characterises
the trade: switches↓/OSPA↓ vs rmse/lifetime↑); recapture
(`imm_cv_ct_mht_recapture`, τ=2) **measured net-negative** — means over
imazu_05–22: id_switches 27.84 → 29.44 (+1.60), breaks 16.82 → 17.73, lifetime
0.933 → 0.928 (−0.005), gospa 27.31 → 27.37. The AutoFerry lifetime catastrophe
is **absent** here because the age-scaling barely engages on position-only
radar+AIS (last-position-anchor age ≈ 0) — a knob behaving differently on
crossing geometry, which is itself the finding.

**Recommendation — frame the trade, not a winner** (not "do nothing, PMBM is
fine": Q2b makes that dishonest). MHT and PMBM fail the same close geometry in
different currencies: **MHT = identity churn, presence preserved** (target stays
in the picture near CPA, label unreliable); **PMBM = track loss, survivor id
preserved** (target can vanish for tens of seconds *at* the CPA, often back under
a new id, plus a steady +0.77 clutter over-count). The choice is operational: if
the consumer needs continuous presence through the encounter (collision
avoidance), PMBM's close-pass dropout is the disqualifier and MHT's churn the
lesser evil; if it needs stable identity for held tracks and tolerates a brief
dropout, PMBM wins. Arbiter/user own the call. Engineering actions: (1) close #11
"MHT identity churn" as *diagnosed*; (2) elevate PMBM close-pass track-loss as
the decision-relevant finding (arbiter's call: new backlog item vs attach to a
PMBM-birth/continuity line — not MHT association); (3) +0.77 over-count is the
parked clutter/birth channel; (4) no #11 knob promotable (leave OFF); (5) if MHT
identity is ever chosen, the lever is duplicate-birth suppression near a
confirmed track, not gate widening — new ticket. Full suite green in the
`backlog11-imazu-churn` worktree: **100% tests passed, 0 failed out of 1090**
(33 fixture-gated non-imazu tests skipped — only imazu/sim_ms fixtures reached
via `SIMMS_DIR`→main tree; the imazu battery tests ran, incl.
`Imazu22ScenarioRun.IdSwitchesCoarseBand`).

Commands (states export is byte-deterministic; re-run checksum verified):
```
SIMMS_DIR=$PWD/tests/fixtures/sim_multisensor ./build/bench/navtracker_bench_baseline \
  --with-imazu --skip-replays --scenario-filter imazu --seeds 1 \
  --config-eq <imm_cv_ct_mht | imm_cv_ct_pmbm_coverage_land | imm_cv_ct_mht_recapture> \
  --run-id <id> --out <dir> --export-states-dir <dir>/states_<cfg>
tools/imazu_switch_forensics.py  --states <states.csv> --meta <meta.txt> --bench-csv <b11_*.csv> --config <cfg> --scenario <case>
tools/imazu_cardinality_timing.py --states <states.csv>
tools/imazu_trackloss.py          --states <pmbm states.csv> --ownship <fixture>/ownship.csv --window 30
```
Fixtures unchanged (sha256 = the 2026-07-08 set below). Reproducer sha256
prefixes: forensics 9504189b, cardinality a417f13a, trackloss 39f0d090; states
CSVs imazu_14/17/20 MHT a550c34c/250e571b/0971e88e, PMBM 39a5c33b/4fbb96b2/
64a1cd28, recapture b08a6048/a707b67d/ca470584.

## 2026-07-08 — Imazu 22 encounter battery: identity stability through close crossings [Cl-3]

The 22 canonical Imazu-problem encounters (head-on / crossing / overtaking
singles up to 3-target combinations) transcribed as fixed-geometry sim scenarios
`imazu_01`..`imazu_22` — a citable regression suite for exactly what crossing
geometry stresses: identity stability through close passes. Own-ship never
manoeuvres (a TRACKER suite, not COLAV); targets run constant-velocity through
CPA/collision geometry. radar+AIS arm; truth independent of every sensor by
construction. Same `SimMultisensorScenarioRun` class as `--with-simms` (new
`defaultImazuScenarios()` factory, `--with-imazu` bench flag, no camera arm),
explicit geometry via `ExplicitInitial` (not trafficgen). Full table + reproduce
in `docs/baselines/2026-07-08_imazu22.md`. No defaults changed; additive and
self-skips when fixtures/`SIMMS_DIR` absent (bench + suite bit-identical without
`--with-imazu`). GOSPA c=20 p=α=2.

**Geometry source:** CORALL `src/utils/imazu_cases.py` (Klins101/CORALL, MIT),
transcribed verbatim (arithmetic as-authored; `Case 23` non-canonical, dropped).
CORALL's non-physical speed scalars are replaced by preserving their tuned
collision RATIO (`18.52/43.3 = 0.4277`) with a physical own-ship speed (20 kn /
targets 8.6 kn); ranges ×0.5 (3-7 → 1.5-3.5 NM) to keep each case ~6-9 min —
both CPA-preserving, leaving all bearings/courses/crossing angles unchanged.
Sources disagree on absolute speed/frame/range scaling (CORALL vs Waltz&Okhrin
arXiv:2211.01004 vs Xie JMSE 12(3):372 vs Lyu JMSE 12(8):1289) but AGREE on the
topology (encounters + 4/7/11 grouping); we picked one and recorded the
divergence. COLREG-role tags are geometry-derived.

**Determinism (a deliverable):** pure function of `(scenario,seed)` —
byte-identical regen (spot-checked imazu_01/12/22) and in-memory `--verify`
passes all 22; bench replay bit-stable (two MHT runs → identical non-timing
metrics). Aggregate `id_sw`/`breaks` are mean-per-truth (imazu_09: per-truth
25 & 32 → 28.5).

**Headline / finding — MHT identity churn on dense crossings (backlog #11
evidence):** single-target cases (imazu_01-04) are clean for both trackers
(0 id-switches). MHT churn then climbs with target count + crossing density to
**imazu_17 72.0**, **imazu_20 68.0**, imazu_21 43.0, imazu_19 42.3, imazu_14
32.0 mean switches/truth — concentrated in the overtaking-heavy 3-target family
(overtaken co-course target + crossers converging on one CPA region, where radar
cross-range error exceeds true separation). Position holds throughout
(RMSE ~25-28 m); it is identity, not position, that breaks. PMBM (coverage_land)
is structurally identity-stable (id-switches 0-8.3 across all 22) but pays with a
persistent over-count (card_err ≈ +0.77 on clean cases, OSPA 130-260 vs MHT
37-195) and, on the densest cases, under-holds (card_err ~0/negative, lifetime
0.67-0.81, breaks 20-32). No clean winner; no tuning applied. The imazu family is
now the controlled instrument for future #11 (MHT association) / PMBM birth work.

**Gate:** `tests/benchmark/test_imazu22_scenario_run.cpp` — 22 labels (radar+AIS
table, no camera), datum+shared-clock truth, sampled per-case determinism, and a
COARSE per-case id-switch tripwire (a band over the measured max + margin, not an
exact pin — the knife-edge lesson holds).

Fixture checksums (sha256 prefix; own / ais / radar / cam / truth;
`b12a6528` = header-only empty camera file, none carry camera):
`imazu_01` 2694811f / 5153b1a3 / 813b7727 / b12a6528 / 599886e6;
`imazu_02` 2694811f / eb30c77e / da0eeba8 / b12a6528 / 89a0dd85;
`imazu_03` 2694811f / 86a44d44 / 4028e065 / b12a6528 / d685f455;
`imazu_04` 2694811f / 6efd27ea / 72fb168d / b12a6528 / f74d32cd;
`imazu_05` 2694811f / 7848d91c / 66d1cd4e / b12a6528 / f84b5da6;
`imazu_06` 2694811f / 70df762a / 3940eacc / b12a6528 / 4fc03a8a;
`imazu_07` 2694811f / 1bbae5a0 / cd42e24d / b12a6528 / 279fc26f;
`imazu_08` 2694811f / 28d5fb60 / b3d0e0de / b12a6528 / 02b5e7af;
`imazu_09` 2694811f / cb1b7238 / 6e35fd0c / b12a6528 / 4a30fec5;
`imazu_10` 2694811f / a20da0bc / b6f41dc1 / b12a6528 / 9beabe37;
`imazu_11` 2694811f / ea5c5661 / 87a97ac3 / b12a6528 / 3bf1286d;
`imazu_12` 2694811f / e615a47d / 5cafc071 / b12a6528 / a6a426a4;
`imazu_13` 2694811f / 766b01c2 / fe9cc7a6 / b12a6528 / 7c3a1eb5;
`imazu_14` 2694811f / 3393d2de / fb938c8b / b12a6528 / c93a3ade;
`imazu_15` 2694811f / 2a1fbe23 / 5a85e17b / b12a6528 / d69eea1d;
`imazu_16` 2694811f / d064cb91 / 64c0d93f / b12a6528 / 0de29a12;
`imazu_17` 2694811f / 28917e73 / 12b3aead / b12a6528 / 5c2c1418;
`imazu_18` 2694811f / 498bebc9 / 093ad54f / b12a6528 / d1978033;
`imazu_19` 2694811f / 9fa0136d / 7eed680e / b12a6528 / 4e7c67d4;
`imazu_20` 2694811f / abd16c8d / f604b911 / b12a6528 / 4db1b1be;
`imazu_21` 2694811f / d05ce174 / c4d55b83 / b12a6528 / 09cc49a5;
`imazu_22` 2694811f / 203384b7 / 25384838 / b12a6528 / cae32a8d.
(Regenerate: `tests/fixtures/sim_multisensor/README.md`, `--family imazu`.)
## 2026-07-08 — Camera chain vs operator: pinned YOLO graded against the R8.8 car_carrier labels [Cl-3 reality-check; NOT a tuning target]

Named follow-up to the 2026-07-06 R8.8 occlusion labelling pass (the camera→
bearing pipeline was deliberately withheld from labelling; now the machine is run
over the same clip and graded against the human labels). One-way: labels grade the
machine, no label edited, no chain parameter tuned. Full write-up +
per-label table + all checksums:
`docs/baselines/2026-07-08_camera_chain_vs_operator.md`. Ticket
`docs/superpowers/plans/2026-07-08-camera-chain-comparison-ticket.md`.

**Calibration gate — PASS.** car_carrier is the 2020 rig; used the bag's OWN cal
files (same camera serials as the committed 2022 cal — same cameras recalibrated
2020-08-21; fx drift −1.5…−2.8% ⇒ ≤0.6° bearing impact). No AIS on 2020 ⇒ boresight
transferred from the 2022 `yaw_offset` (2.29217° center, −42.971° left) and
validated against RADAR (independent; `azimuth_deg` is hull-relative, so directly
comparable to camera `bearing_rel`). Signed camera−radar residual median **+0.31°
(center, n=948) / +0.08° (left, n=555)** with NO offset fitted → transferred
boresight has no measurable systematic bias on the 2020 rig. Radar ≠ camera ≠
labels, so non-circular.

**Detector run.** Pinned `yolov8n.pt`
(sha256 `f59b3d83…c83b36`), ultralytics 8.4.87 / torch 2.12.1+cpu / cv2 5.0.0 /
py3.12, `conf=0.25 imgsz=1280 class=8`, center+left, 2×1451 frames → **3086 + 1591
detections** (`_camera_detections.csv` sha256 `9a24b313…5222908`). Clip registered
at runtime (CLIP_MAP injection) so the pinned script stays byte-identical.

**Findings (for the arbiter).** (1) **`carrier_gl_a/b` label COORDINATES are
inconsistent** — tagged `nearestbig{60,95}` yet their lat/lon back-projects to
+8…+16° starboard while the actual radar nearest-big <300 m is at −137° port
(~400 m off); the label *text* (port/left-cam) is right, the *coords* are not.
NOT edited — flagged upstream. (2) **Bearing-only + point labels can't attribute
co-bearing detections**: the port sector is crowded, so `unknown_w860`/`yacht_moored_2`
"partial" (cov 0.32–0.36) is entirely the CARRIER crossing their bearing (ambig=1.00);
independent 860 m yacht detection ≈4% = a recall/range limit (bearing tight, 2.55°
median, when it does fire). (3) **Carrier handled well**: single clean box in the
LEFT camera on the port bow/beam (bearing −22°→−62°), fragmentation in only 4/32
big-box frames, max ~12% frame area — it does NOT fill the frame (crossing at
143–269 m); extreme-scale fragmentation NOT observed. (4) **Shadow interval t50–85
confirmed**: at the yacht bearing the left cam shows the large carrier box (t50–60)
then nothing (t65–85) — the yacht is never independently detected; silence =
"not observed", never "observed empty". (5) `yacht_exit_port` + `sail_close_end`
are clean unambiguous hits; `portq_object` (SUPPRESS_STRUCTURE) is correctly never
in any camera FOV. Annotated frames rendered LOCAL only (license boundary;
11 frames, checksums in the baseline doc).

## 2026-07-07 — LOS/shadow guard SHIPPED (verdict-b fix): coverage-aware decay no longer erodes a shadowed moored vessel; two gate-correctness rulings [Cl-3 / ADR 0002]

Implements the 2026-07-06 shadow-probe verdict-b fix (ticket
`2026-07-06-los-guard-ticket.md`): coverage-aware occupancy decay must not treat
a cell whose line of sight is blocked by a closer occluder as "observed empty".
Geometry `core/static/ShadowMask.hpp` (pure, unit-tested); wired into the decay
loop `LiveOccupancyModel::observe`; ON in `imm_cv_ct_pmbm_occupancy_detector_coverage`
via per-instance `LiveOccupancyParams::shadow_guard` (default OFF ⇒ every other
config byte-identical).

**The fix works (car_carrier_near, unknown_w860 yacht cell, guard ON vs OFF):**

| interval        | mass0→massT (OFF) | mass0→massT (ON) | hazard OFF→ON | guard fired |
|-----------------|-------------------|------------------|---------------|-------------|
| shadow 50-85 s  | 0.141 → **0.006** | 0.504 → **1.566** | **51% → 100%** | **9/9 swept** |

Shadow mean mass 0.073 → **1.510 (20.7×)**, hazard presence **51% → 100%**, decay
events 10 → 0. The occluded moored yacht's occupancy evidence is held through the
35 s passage instead of eroding. Peak guard-protected cell fraction 10% (narrow
shadow sectors — sane). Test `LosShadowGuard.CarCarrierNearYachtCellGuardOnVsOff`.

**No false shielding:** sim control `sim_ms_anchored_camera` (no persistent
occluder) — guard fires 1/15 swept scans (7%, a real transient crossing), mass Δ
≤ 0.0009: near-inert. Default configs (occupancy OFF) byte-identical by
construction (guard gated behind `use_live_occupancy_model` + `shadow_guard.enabled`);
full suite 1078/1078 green, philos KEEP gates untouched.

**Calibration — physically derived, NOT swept-to-green (anti-overfit):**
`min_occluder_returns = 1` (the tracker feeds CFAR PLOTS at ~4/scan — each is a
real reflector, so a single closer plot blocks LOS; n_cells/amp does not survive
to the occupancy feed), `wedge_pad ≈ 3σ_az` (σ_az ≈ 1.6°), `range_margin = 50 m`
(occluder radial extent + ~1σ_r, σ_r ≈ 25 m — just enough not to clip the
occluder's own far edge). **`range_margin = 400 m` was the ONLY setting that kept
the 6c emitted-hazard gate green as-is, and was REJECTED as an overfit passing
point on the sunset knife-edge** (see the second ruling below).

**HAXR delta (fixed shore station kattwyk_08 decimated — "say what you find"):**
the ticket guessed near-inert; the finding is the guard is **active AND net
beneficial**, no regression — a shore station still has ships occluding shore
structure, so the guard holds it:

| metric | guard OFF | guard ON |
|---|---:|---:|
| card_err_mean | 44.40 | **41.46** |
| gospa_mean | 100.26 | **97.46** |
| gospa_false | 9707 | **9119** |
| gospa_missed | 827.75 | 827.75 |
| lifetime_ratio | 0.0957 | **0.1045** |
| occ_peak_structures / suppress_hits | 27 / 26 633 | 37 / **50 151** |

Suppression ~doubles but falls on CLUTTER, not vessels (gospa_missed FLAT,
gospa_false DOWN). Test `LosGuardHaxrAB` (skip-guarded on local-only fixtures).

**Ruling 1 — decouple the guard from the clutter-adaptive bar (semantic fix).**
Holding shadowed mass raised the median-based clutter bar → de-emitted marginal
structure. Fix: a cell the LOS guard is protecting this scan is EXCLUDED from the
clutter-background median (a shadowed real object is not clutter; feeding its held
mass into the background estimate was a category error, invisible until the guard
gave those cells mass worth noticing). State-scoped (only while protected); its
own classification against the bar is unchanged; guard OFF ⇒ empty set ⇒ median
byte-identical. No feedback loop: the guard's fire decision is PURELY geometric
(occluder returns), independent of persistence/bar. `LiveOccupancyModel.cpp`.

**Ruling 2 — the 6c "monotonicity" gate asserted a non-invariant; corrected.**
`test_philos_occupancy_coverage_6c` assertion (2) claimed coverage-aware holds
every region ≥ universal (emitted hazard-scans), "from per-cell persistence →
hazard superset". BOTH forms are false as full-pipeline invariants: (a)
emitted-hazard — the clutter-ADAPTIVE bar is non-monotone in persistence (more
mass → higher median → higher bar → can de-emit a region whose mass rose); the
failing region flipped midriver_grp↔astern_blob as the guard margin changed
(50→0/15, 150→0/0, 250→93/0, 400→606/60), an epsilon-knife-edge, not an
invariant. (b) per-cell persistence — NOT monotone between these two configs
either, because the occupancy layer is FEEDBACK-COUPLED to the tracker
(persistence → suppression → tracker → claim pattern → 1−r weights → touches →
persistence): `cov`/`uni` are different runs with different inputs (measured
deficit 0.064). Asserting a property of the DIFFERENCE between two full-pipeline
runs of a feedback system pins an incidental, not an invariant — the old check
was true by luck. Assertion (2) removed (documented in place); the guard's REAL
invariant (identical inputs ⇒ only skips decays ⇒ persistence only rises) is
proven where it holds — `LiveOccupancyModel.ShadowGuardOnlyAddsMassOnFixedInputs`.
Reported observations at the shipped margin: midriver_grp 9→0, astern_blob 10→15
(both med-confidence, satellite-pending SUPPRESS_STRUCTURE). Checks (1)/(3)/(4)
and the KEEP conservation gates untouched.

**LOS guard is NOT implemented as a special case of coverage** — it is the
coverage decay's LOS assumption made explicit; the two rulings above are logged
to the backlog as the week's 4th epsilon-fragility case (adaptive/threshold &
feedback-coupled-A/B decision robustness).
## 2026-07-08 — D8 R-BAD berthing: first fixtures + label-scored replay (fixed body frame; cross-tracker consistency) [Cl-3 reality-check; NOT a tuning target]

Executes the D8 feasibility GO's named next step (2026-07-06, 30323ac): extract
fixtures from the R-BAD berthing dataset + run a label-scored replay. Branch
`d8-rbad-extraction`. **REGIME CAVEAT (governs every number below): R-BAD is
automotive/industrial mmWave FMCW radar (TI IWR6843 60–64 GHz + AWR1443/1642/1843
77–81 GHz), NOT marine X-band. It corroborates the berthing SCENE on a new sensor
class; nothing here is a marine-radar number and philos/HAXR tuning does not
transfer. No config was tuned to this data.**

**Step 1 — four confirm-at-extraction flags, all RESOLVED empirically** (the MDPI
paper stayed 403 bot-blocked on both mdpi.com and IEEE, so the DATA is the
authority; the raw archive was inspected via a ZIP64 central-directory HTTP-range
probe, NOT downloaded):

| flag | resolution |
|---|---|
| (a) CSV columns + frame | Raw `…/<Scenario>/<Port>/<name>.csv`: `Frame Number,POSIX Timestamp,AWR1443,AWR1642,AWR1843,IWR6843` — one point-cloud per chip, each point `[x,y,z,v_doppler,snr]`, **Cartesian body-frame metres**, absolute POSIX time, 20 Hz. Labelled: `Time,Frame_ID,Tracking_ID,X,Y,Z,Num_Points,Points,Dock_Label`. |
| (b) label provenance | **Circular for kinematic/ID truth.** Labelled `Points` match the raw points exactly → clusters + `Tracking_ID` are the authors' OWN onboard clustering/tracking pipeline = a REFERENCE TRACKER, not ground truth. `Dock_Label` binary (0/1), meaning unconfirmed. ⇒ scored at **cross-tracker consistency** grade only. |
| (c) ego pose | **NONE anywhere** — no nav/GPS/IMU file in the 1252-entry raw archive (0 keyword hits), no ownship columns in raw or labelled CSVs. Pure sensor body frame. |
| (d) range/scan | 4× TI mmWave FMCW chips (above); **20 Hz**; observed range **≤ ~56 m**; forward-looking narrow azimuth (±~9.4 m lateral). |

**Scope decision (arbiter, Option A + 5 riders).** No ego pose was the ticket's
designated stop-and-report gate. Ruling: replay as a **fixed body-frame relative-
tracking scene** (own-ship = origin; body frame ≡ fixed ENU, E=X starboard, N=Y
forward) built from the **31.2 MB labelled buffers only** (their `Points` column
carries the per-plot cloud; the 31.6 GB raw is video-dominated). NOT broadened to
visual-odometry ego-pose recovery (worst effort-to-evidence for a sensor class the
deployment will not carry).

**⚠ ADR-0002 exclusion (rider 3):** with no ego pose, nothing is world-stationary
in a body frame, so the anchored/moored static-hazard logic is **UNTESTABLE here
by construction** — its non-firing on R-BAD is **not evidence of anything**.

**Extraction.** `tests/fixtures/rbad/generator/extract_rbad.py` (stdlib only,
committed source; data + derived fixtures local-only via the sim_multisensor
gitignore-negation). 6 arrival approaches across 2 ports (Kalimnos, Kos), ~28 min
of ~1 Hz labelled data — the labelled buffers are sub-sampled to 1 Hz for
annotation, so `tod` is derived from `Frame_ID`/20 Hz. A **representative subset**
of the ~121 min of labelled arrivals available locally across 13 ports (NOT
silently capped — the full set is one edit to `SCENARIOS` away). Plot input =
cluster **centroids** (plot-level, per the extraction-boundary ruling — rider 2),
never the raw constituent points.

**Data-integrity finding + R8.8 fail-loud guards.** A few buffers assign TWO
`Tracking_ID`s to ONE physical detection (identical `Frame_ID,X,Y,Z,Num_Points`,
occasionally conflicting `Dock_Label`) — an annotation artifact. Feeding two
identical plots would inject a duplicate detection cloud (the clutter_burst
duplicate-cloud lesson), so exact-centroid double-labels are collapsed to one
plot/reference, lowest `Tracking_ID` kept (kalimnos_3: 11 collapsed, kalimnos_17:
1, others 0). Every buffer passes 11 fail-loud integrity guards BEFORE any write
(plausible ~20 Hz rate; dynamic non-placeholder ranges/bearings/positions;
|Doppler| ≤ 10 m/s; SNR ∈ (0,60] dB; binary Dock_Label; ≥ 2 reference IDs); on any
violation the extractor names the buffer and writes NOTHING (all-or-nothing).
Re-runs are byte-identical.

**Doppler + SNR carried (rider 4).** `radar_plots.csv` carries `v_doppler_mps` +
`snr_db` as trailing columns beyond the 8 standard plot columns (`loadPlotCsv`
reads the first 8 and ignores extras). First in-hand dataset with per-detection
Doppler (−0.6…0.5 m/s, berthing-slow); **columns only, no analysis** — a future
deployment-hardware Doppler probe becomes an afternoon, not a re-extraction.

**Checksums** (sha256; Zenodo `Labelled Buffers Data.zip` md5
`894a55b05552c57b85e60535fe433e85`; raw archive md5
`ebf21c27637602463a84e701065aa330`, NOT downloaded):

```
30510dd7…  rbad_kalimnos_3/radar_plots.csv     53084bd3…  rbad_kalimnos_3/reference_tracks.csv
fb1edf80…  rbad_kalimnos_16/radar_plots.csv    768284cf…  rbad_kalimnos_16/reference_tracks.csv
1b442f1f…  rbad_kalimnos_17/radar_plots.csv    a844a67e…  rbad_kalimnos_17/reference_tracks.csv
9e0ac22d…  rbad_kos_11/radar_plots.csv         7fe6fb24…  rbad_kos_11/reference_tracks.csv
d17f3944…  rbad_kos_16/radar_plots.csv         5811ab92…  rbad_kos_16/reference_tracks.csv
fdfb8498…  rbad_kos_5/radar_plots.csv          27bf4dd2…  rbad_kos_5/reference_tracks.csv
```
(full 18-line list incl. meta.txt in `tests/fixtures/rbad/CHECKSUMS.txt`)

**Wiring.** `RbadScenarioRun` (`adapters/benchmark/RbadScenarioRun.{hpp,cpp}`,
env `RBAD_DIR`, skip-guarded, single station "rbad" at ENU origin, nominal datum),
bench flag `--with-rbad`, test `tests/benchmark/test_rbad_scenario_run.cpp`
(skip-guarded, loader-determinism, MHT smoke + consistency print). Detection table
= one radar entry with **UNTUNED nominals** (P_D 0.9, λ_C 1e-6 m⁻², 80 m coverage)
— not fitted to this data.

**Results — cross-tracker CONSISTENCY vs the authors' reference tracker, NOT
accuracy (mmWave FMCW, NOT a marine-radar number).** Localization/RMSE are omitted
on purpose: both trackers sit on the same centroids, so localization ≈ 0 and would
be a meaningless "accuracy" artifact. `card_err` is signed per-tick cardinality vs
the reference (+ = we hold more tracks/tick). (Caveat for anyone reading the raw
dump: `--with-rbad` routes through the shared Sweep, whose CSV emits the *uniform*
metric schema — so it DOES contain accuracy-named columns `pos_rmse_m`, `ospa_*`,
`gospa_localization` for `rbad_*` rows, scored against the reference tracker. Those
are the same ≈0 same-centroids artifacts and **must not be quoted as accuracy**;
only the continuity/cardinality columns in the table above carry signal.)

| config | scenario | lifetime_vs_ref | id_switches_vs_ref | breaks_vs_ref | card_err_vs_ref |
|---|---|--:|--:|--:|--:|
| MHT `imm_cv_ct_mht` | rbad_kalimnos_16 | 0.951 | 1.31 | 0.01 | +1.06 |
| MHT | rbad_kalimnos_17 | 0.947 | 1.25 | 0.00 | +0.50 |
| MHT | rbad_kalimnos_3 | 0.932 | 0.45 | 0.02 | +0.60 |
| MHT | rbad_kos_11 | 0.868 | 0.98 | 0.04 | +0.53 |
| MHT | rbad_kos_16 | 0.824 | 0.75 | 0.00 | +0.49 |
| MHT | rbad_kos_5 | 0.861 | 0.86 | 0.05 | +0.19 |
| PMBM `imm_cv_ct_pmbm_coverage_land` | rbad_kalimnos_16 | 0.923 | 0.28 | 0.04 | +0.68 |
| PMBM | rbad_kalimnos_17 | 0.846 | 0.18 | 0.02 | +0.29 |
| PMBM | rbad_kalimnos_3 | 0.931 | 0.13 | 0.02 | +0.58 |
| PMBM | rbad_kos_11 | 0.902 | 0.14 | 0.03 | +0.46 |
| PMBM | rbad_kos_16 | 0.870 | 0.14 | 0.02 | +0.44 |
| PMBM | rbad_kos_5 | 0.762 | 0.14 | 0.10 | +0.11 |

Dock_Label distribution (reported, **not asserted** — rider 1; meaning
unconfirmed): label-1 fraction per buffer ranges 0.21 (kalimnos_17) → 0.47
(kalimnos_3); ~32% across the full labelled set.

**Findings for the arbiter (report only — the ticket's interesting questions):**
- **Berthing-speed continuity: holds, no fragmentation.** breaks ≈ 0, lifetime
  0.76–0.95 across both trackers — navtracker holds one stable track where the
  reference held one ID through the slow, close-range, maneuvering approach. PMBM
  id_switches (0.13–0.28) < MHT (0.45–1.31): more stable identity.
- **Over-count on a different clutter class: mild per-tick, FEWER IDs over a run.**
  card_err is a small positive (+0.1…+1.1 tracks/tick), yet over a whole buffer
  navtracker uses far fewer distinct track IDs than the reference has (e.g.
  kalimnos_16: 130 ours vs 235 reference) — the reference spawns many single-frame
  transient IDs that navtracker's confirmation correctly does not promote. On this
  mmWave clutter the behavior is the OPPOSITE of the philos over-count:
  conservative, not exuberant. Observed with the untuned λ_C nominal; NOT tuned.
- **Anchored/moored logic: not evaluated** (see ADR-0002 exclusion above).

**Deferred route (rider 5).** The 31.6 GB Raw Aggregated Frames archive
(video-dominated) stays UNDOWNLOADED. Its only added value is the synced MP4 for
an independent manual video-label pass (the philos R8 workflow), which yields the
one thing missing here — independent KINEMATIC truth. Trigger, recorded
explicitly: **download + commission the video-label pass only if a berthing-scene
result ever needs independent kinematic truth.**

**Determinism.** `--with-rbad` PMBM run twice: 0 differing data-metric cells
(wall/scan-latency excluded) — byte-identical. Loader determinism pinned by
`RbadScenarioRun.DeterministicReplay`.

**Suite / fixture-trap (ran-vs-skipped).** The R-BAD fixture-gated tests were RUN
(not skipped) against the MAIN-tree fixtures via
`RBAD_DIR=<main>/tests/fixtures/rbad`: `RbadScenarioRun.*` 4/4 pass, replay 0.55 s
for all 6 scenarios; both `--with-rbad` configs complete in ~1 s (stop-condition
was >10 min). This is REQUIRED because `tests/fixtures/` is gitignored and empty in
the worktree (the fixture-trap rule). Full worktree suite (RBAD_DIR set): **1076/1076
passed, 0 failed** (75.6 s), incl. the integration-guide config-coverage drift
test. 78 other-dataset fixture-gated tests (philos/haxr/simms) skip in the
worktree — their data lives only in the main tree and this change does not touch
them.

## 2026-07-06 — nav_status-gated velocity suppression (#20 sub-item b): correct guard; proof re-pinned to the right level [Cl-3]

Ships the fix candidate the velocity-path pricing surfaced: an anchored (1) /
moored (5) vessel's watch-circle SOG must not become PositionVelocity2D content.
Implemented as a shared predicate `aisNavStatusSuppressesVelocity` in
`core/estimation/PolarVelocity.hpp`, gated at BOTH call sites (NMEA `AisAdapter`
and replay `loadAisCsv`) so the paths stay locked together. TDD'd (RED→GREEN):
`AisAdapter.AnchoredNavStatusSuppressesVelocity`,
`AisAdapter.MooredSuppressesButUnderwayStillEmitsVelocity`,
`AisCsvReplay.AnchoredNavStatusSuppressesVelocityWhenOn`, plus the invariant
pin `AisCsvReplay.AnchoredVesselKinematicsIdenticalOnVsOff`. Full suite
**1067/1067**.

**Proof, stated at both levels honestly (the acceptance level was corrected —
see ruling below):**

- **Per-target MEASUREMENT identity for the anchored vessel — MET (the
  correct-level proof).** With the gate, anchored vessel 601's (nav_status=1)
  kinematic measurement content — model `Position2D`, position value,
  covariance — is byte-identical velocity-ON vs velocity-OFF, even on the rows
  above the SOG threshold (unit-pinned by `AnchoredVesselKinematicsIdenticalOnVsOff`).
  The only ON/OFF difference is the surfaced `nav_status` hint, which in the
  `imm_cv_ct_mht` path is metadata-only (copied to `tree_attributes_`, not a
  veto — verified). So an anchored vessel can no longer destabilize its OWN
  track via velocity. This is stricter evidence than any aggregate row.

- **Scenario-row inertness — NOT achievable on this fixture (and not by any
  nav_status gate).** The `sim_ms_anchored_camera` row does not go inert:

  | metric (Δ = ON − OFF, `imm_cv_ct_mht`) | pre-gate | with gate |
  |---|---|---|
  | anchored ospa_mean | +10.5 | **+8.5** |
  | anchored track_breaks | +5.3 | **+5.3 (unchanged)** |

  Decomposition explains why. The fixture bundles anchored 601 (4 AIS rows, only
  2 above threshold at 0.51/0.59 m/s) with an UNDERWAY vessel 603 (100 rows at
  9.9 m/s, nav_status=0). The gate suppresses 601's 2 spurious emissions — that
  is the entire 10.5→8.5 improvement — but 603's velocity is legitimate and
  correctly untouched. Per-target, 601 still regresses ON (breaks +7, sog_rmse
  30→87) despite its own stream being identical ON/OFF: pure **cross-target
  coupling** — 603's velocity churns the shared MHT hypothesis/association state
  and drags the anchored track with it. That residual is the general continuity
  regression, **#20 sub-item (a)**, explicitly out of this ticket's scope and
  not addressable by nav_status gating.

**Ruling (arbiter, 2026-07-06):** the assignment's acceptance criterion ("the
anchored sim scenario must go inert") was pinned at the wrong level — the
scenario row measures two things at once (the anchored vessel's emissions AND
the underway vessel's cross-coupling). The gate's actual promise is that the
anchored vessel's spurious emissions stop, and the per-target measurement
identity above proves exactly that. Recorded here so the correction is
traceable to the arbiter, not silently absorbed.

**Default behavior priced.** `loadAisCsv` default-off (emit_velocity=false):
byte-identical (gate never fires; confirmed gate_off == pre-gate off on all
deterministic rows). `AisAdapter` (NMEA, velocity default-on): now suppresses
velocity for nav_status ∈ {1,5} + SOG>threshold — accepted as the semantically
correct behavior (watch-circle jitter is not a track velocity); change surface
is exactly that corner. The gate is narrow: the underway scenarios
(`sim_ms_headon`, `sim_ms_overtaking`) are byte-identical pre/post gate.
## 2026-07-06 — D7 MOANA dataset: feasibility NO-GO for our (commercial) context [Cl-3 feasibility; no extraction done]

Feasibility-only assessment of the MOANA dataset (pre-water item 7,
`docs/superpowers/plans/2026-07-02-data-expansion-todos.md` §D7). Verdict:
**NO-GO** for navtracker's commercial context — two independent hard reasons
(non-commercial license; no Doppler in the published data), plus a format
mismatch. Desk check only, no extraction. Sources are the arXiv full text and
the dataset's own download page (both accessible, unlike the D8 MDPI paper).

**What it is.** "MOANA: Multi-Radar Dataset for Maritime Odometry and
Autonomous Navigation Application", arXiv 2412.03887 (IJRR 2025), KAIST RPM
lab. 7 sequences (2 port, 5 island). Sensors (Table 2): X-band **SIMRAD
HALO4** (9.41–9.50 GHz, 2498 m, 2.44 m/px) + W-band **Navtech RAS6**
(76–77 GHz, 600 m, 0.175 m/px) + short-range LiDAR + stereo camera +
Hemisphere V500 RTK GNSS (position + heading). Project:
sites.google.com/view/rpmmoana; code: github.com/hyesu-jang/LodeStar.

**License — commercial: NO-GO (decisive).** The dataset download page states
**CC BY-NC-SA 4.0** — "you may not use the work for commercial purposes."
This is the dataset's OWN license (not merely the arXiv paper's submission
license — I checked the project page directly, the D8 paper-vs-dataset lesson).
For a TKMS product this is a hard blocker: NonCommercial disallows
product-directed use, and ShareAlike would virally require any distributed
derivative (e.g. fixtures baked into this repo) to be CC-BY-NC-SA —
incompatible with a proprietary codebase. (Contrast D8 R-BAD: CC-BY-4.0,
commercial OK.) The only lawful path to MOANA for us would be a separate
commercial-license grant negotiated with the authors — out of scope here.

**Per-detection Doppler (the arbiter's question b): NO — and this corrects
the roadmap.** Both radars are *imaging* radars whose released data are PNG
intensity images: X-band as Cartesian intensity maps, W-band (Navtech RAS6)
as polar→Cartesian 1024×1024 PNG. Neither exports per-detection radial
velocity; the W-band is a scanning imaging radar, **not** a 4D
(range-azimuth-elevation-Doppler) automotive radar. The published data has no
Doppler channel — the increment-8 Doppler/MTI direction **cannot** be
prototyped on MOANA. This contradicts the pre-water-window plan (§ item 7,
"a Doppler-capable radar (W-band)") and the comparison-baselines row that both
sell D7 partly on Doppler; that premise is mistaken and should be struck.

**Truth / AIS-independence (the arbiter's question a): YES — the one real
positive.** Object labels are 2D bounding boxes produced by radar + stereo-
camera visual inspection (X-band, W-band, and stereo), and pose ground truth
is Hemisphere V500 RTK GNSS with heading. **AIS is used nowhere in MOANA** (the
single "AIS" mention in the paper cites a *different* dataset). So MOANA genuinely
is the AIS-independent labelled marine radar we lack — but the bounding-box
labels are provided for **only the Single Island sequence** (1 of 7), so the
labelled coverage is thin, and it is legally unusable for us regardless.

**Format vs our model: poor fit (hits the parked extraction boundary).** The
X-band output is a Cartesian **intensity image** (PNG), not a range/azimuth
detection/plot list. Our replay adapters consume `radar_plots.csv`
(range/azimuth *plots*). Turning MOANA imagery into plots requires CFAR/
detection + clustering on the raw image — i.e. front-end extraction, which
the 2026-07-06 ruling parked as upstream's job, not navtracker's. This is
strictly heavier than D8's ready-made CSV detections.

**Download/storage cost: not confirmed (moot).** The download subpage was not
read; multi-radar PNG imagery + LiDAR + stereo across 7 sequences is likely
tens–hundreds of GB. Moot given the license NO-GO.

**Net.** NO-GO. MOANA does fill the sorest gap on paper — AIS-independent
labelled marine (X-band) radar with anchored large vessels — but (1) its
CC-BY-NC-SA license bars commercial use, (2) it has no per-detection Doppler,
so the second half of D7's rationale is void, and (3) its raw-imagery format
needs front-end extraction we've deliberately parked. If AIS-independent
marine-radar truth ever becomes essential, the action is a commercial-license
conversation with KAIST, not extraction under the current terms. Net effect on
the queue: D7 does **not** unblock the increment-8 Doppler direction; that
still waits on deployment-hardware answers.

Sources: arXiv 2412.03887 full text (sensor Table 2, PNG image formats, GNSS
truth, labels on Single Island, no AIS); dataset page sites.google.com/view/
rpmmoana (CC-BY-NC-SA 4.0, "no commercial use").
## 2026-07-06 — LOS/shadow probe (R8.8 payoff): coverage-aware decay DOES erode a shadowed moored vessel — bounded, self-healing false-fire (verdict b) [Cl-3 / ADR 0002]

MEASUREMENT ONLY (ticket `docs/superpowers/plans/2026-07-06-los-shadow-probe-ticket.md`).
Wires the R8.8 occlusion clip `car_carrier_near` through the coverage-aware
occupancy-decay arm and asks, against measured truth, whether the shadowed moored
yachts (`unknown_w860`, radar-silent t 50-85 s while GENTLE LEADER crosses their
bearing at 150-250 m) are treated as "observed-empty" and lose occupancy evidence.
No decay-model behaviour changed; the probe reads `persistenceCells()` + the
recorded coverage sectors via an **additive, opt-in, default-inert** capture in the
shared label-replay harness (`tests/replay/PhilosLabelReplay.hpp`,
`capture_persistence`, off for every existing caller ⇒ byte-identical).

**Ticket config-name correction (load-bearing).** The ticket names
`imm_cv_ct_pmbm_coverage_land` as the layer to exercise. That config wires the
sensor-activity **duty-cycle** coverage model + land prior and NEVER the
`LiveOccupancyModel` / coverage-sector decay (`Config.cpp:1142`) — running it would
falsely read as verdict (c) "layer doesn't fire". The coverage-aware occupancy
**decay** arm is `imm_cv_ct_pmbm_occupancy_detector_coverage` (`Config.cpp:903`,
`use_live_occupancy_model` + `estimate_coverage_sector`). The probe uses the config
that actually exercises the layer under test.

**Result — unknown_w860 yacht cell (ENU (−1014, 97) m, range ≈ 1018 m; cell 100 m):**

| interval        |   n | mass0 | massT | mean  |  max  | swept | hazard | touch | decay |
|-----------------|----:|------:|------:|------:|------:|------:|-------:|------:|------:|
| pre  5-50 s     | 407 | 0.108 | 0.141 | 0.091 | 0.195 |  4.7% |  72.0% |     8 |    10 |
| **shadow 50-85 s** | 317 | 0.141 | **0.006** | 0.073 | 0.168 | **3.8%** | **50.8%** | **2** | 10 |
| post 85-120 s   | 323 | 0.006 | **0.191** | 0.110 | 0.191 |  5.0% | **99.7%** |    10 |     6 |

Coverage sectors: 1102 valid, **median width 13°**, 0 full-circle.

**Sim control** `sim_ms_anchored_camera` (anchored vessel, NO occluder; ENU
(−1602, 1079) m). Confirms the decay mechanism operates absent any occlusion, but
this cell is a low-mass / sparse-touch regime (never a stable hazard) — a weaker
magnitude baseline than the within-clip pre/post:

| window          |  n | mass0 | massT | mean  |  max  | swept | hazard | touch | decay |
|-----------------|---:|------:|------:|------:|------:|------:|-------:|------:|------:|
| 5-50 s          | 18 | 0.064 | 0.005 | 0.021 | 0.064 | 38.9% |  27.8% |     0 |     7 |
| 50-85 s         | 14 | 0.005 | 0.003 | 0.003 | 0.005 | 42.9% |   0.0% |     1 |     5 |
| 85-120 s        | 14 | 0.003 | 0.001 | 0.002 | 0.003 | 14.3% |   0.0% |     0 |     2 |

**Cross-check (validates the probe + the coverage gate).** Mass changes ONLY on
swept scans, exactly as `LiveOccupancyModel.cpp:111-122` specifies: touch+decay per
interval ≈ swept count (car_carrier pre 8+10≈19, shadow 2+10≈12, post 10+6≈16; sim
same). Decay events ARE "observed-empty" calls; touches are returns reinforcing the
cell.

**Finding.** (1) The occluder does **not** inflate the observed-empty rate: decay
events are flat across intervals (10 pre / 10 shadow / 6 post), and the shadow
swept-fraction (3.8%) is if anything *below* pre/post (4.7%/5.0%). The narrow
per-burst sectors (median 13°) that range-truncate at the carrier keep the shadowed
cell mostly un-swept — so the sector estimator is NOT mistaking the shadow for open
water at scale. (2) But the residual ~10 observed-empty decays over the 35 s are
now **unopposed**: the shadow converts touches to decays (8→2) by removing returns,
so the yacht cell's mass collapses **24×** (0.141 → 0.006) and its emitted hazard's
presence drops **72% → 51%**. Those ~10 decays are observed-empty calls on a
physically-occluded cell — the LOS-guard's exact target. (3) The degradation is
**transient and self-healing**: within ~35 s post-shadow the mass recovers to 0.191
and hazard presence to 99.7%. The ADR-0002 presence channel is degraded during the
passage but not lost, and rebuilds once returns resume.

**Verdict (b): a real but bounded, self-healing shadow false-fire.** Magnitude:
~10 observed-empty decays / 35 s → cell mass 24× erosion + hazard presence 72%→51%,
recovering fully after the occluder clears. It is NOT the clean "excluded by
construction" (a) — the cell IS decayed as observed-empty on the scans a sector
covers it — but it is far from catastrophic: the occluder doesn't inflate the decay
rate, and the effect self-heals. **Arbiter's call** whether the sketch below is
worth it against this bounded magnitude (per the ticket, no LOS guard implemented).

**LOS-guard design sketch (for the arbiter — NOT implemented).** In the coverage
decay loop (`LiveOccupancyModel::observe`, `.cpp:110-122`), before decaying a cell
that a sector covers, suppress the decay if the sensor recorded a **strong closer
return on the same bearing** this scan (a shadow: the echo truncated before the
cell). Concretely: carry per-scan (bearing, range) returns alongside the
`CoverageSector`; a cell at (θ_cell, r_cell) is shadowed — skip its decay — if some
return exists at |θ − θ_cell| ≤ ~half a beamwidth with range r < r_cell − margin.
Cost: one extra per-cell bearing test against the swept returns; safe direction
(skipping a decay only holds a hazard longer, never emits a false one — same safety
argument as the existing under-estimated-coverage design, `ISensorDetectionModel.hpp:160`).

**Acceptance:** interval table (pre/shadow/post + sim control) committed here;
diagnostics additive + default-inert (existing occupancy/label tests byte-identical);
no decay-model behaviour changed; full suite green; probe skip-guards on fixture
absence. Test `tests/replay/test_philos_los_shadow_probe.cpp`
(`LosShadowProbe.CarCarrierNearYachtCell` / `.SimAnchoredControl`). Fixtures
local-only (`car_carrier_near`, `sim_ms_anchored_camera_s0`). See the R8.8 labelling
pass entry below (same date) for the ground-truth provenance.

## 2026-07-06 — Replay AIS loader velocity path (#20) first measured against honest truth [Cl-3]

`loadAisCsv` can now emit PositionVelocity2D (SOG/COG) + `hints.nav_status` from
the columns the fixtures already carry, behind a **default-off** toggle
(`emit_velocity` param; bench env `SIMMS_AIS_VELOCITY` / `PHILOS_AIS_VELOCITY`).
The polar-Jacobian + isotropic-floor math is EXTRACTED into a shared helper
`core/estimation/PolarVelocity.hpp` that both the NMEA `AisAdapter` (increment 2)
and the replay loader call — no duplicated Jacobian, the paths cannot drift
(unit test `AisCsvReplay.MatchesAisAdapterVelocityContent` pins them equal). This
is the first time the #20 velocity path runs through the full MHT/PMBM pipeline
scored against truth that is independent of AIS (sim gates).

**Default-off byte-identical (proven):** unit test (default → Position2D); the 7
`AisAdapter` tests stay green (the extraction is a mechanical, byte-identical
move); bench byte-compare on the sim-ms battery (MHT, all 6) branch-vs-master is
identical on every metric row; full suite green with the pinned philos replay
tests (which drive `loadAisCsv` default-off) unchanged.

**ON pricing — sim gates, honest truth by construction (Δ = ON − OFF):**

MHT `imm_cv_ct_mht` — velocity trades id-switches for track continuity:
| scenario | ospaΔ | id_swΔ | breaksΔ | lifeΔ | cardΔ |
|---|---|---|---|---|---|
| headon          | +59.3 |   0.0 | **+30.0** | −0.12 | +0.03 |
| ais_dropout     | +59.2 |  +3.0 | +14.0 | −0.07 | +0.06 |
| overtaking      | +28.4 | **−10.5** | +12.0 | −0.05 | +0.00 |
| crossing        | −11.1 | **−6.3** |  −2.3 | +0.00 | −0.09 |
| clutter_burst   | −25.2 | −1.5 |  +9.0 | −0.04 | −0.27 |
| anchored_camera | +10.5 | −0.3 |  +5.3 | −0.05 | −0.15 |

PMBM `imm_cv_ct_pmbm_coverage_land` — net small regression, NO id-switch benefit
(PMBM identity is already structurally 0 switches): ospa worse everywhere (+3 to
+39), breaks mostly worse, `card_err` marginally better (−0.02..−0.12), lifetime
slightly worse. philos ais_ferry_far (MECHANICS ONLY — AIS-derived truth, so a
velocity arm scored against it is CIRCULAR, not an accuracy signal): same
direction — lifetime 0.42→0.10, ospa 356→447, rmse 25→50.

**Finding (for the arbiter; no default flipped, no config promoted):** correct
velocity content — verified sane (AIS SOG 6–7 m/s; the loader matches AisAdapter
to 1e-6) — is NOT a free win. It sharply cuts id-switches on MHT maneuvering
targets (crossing −6.3, overtaking −10.5) but REGRESSES continuity broadly (track
breaks, lifetime, OSPA), most starkly on the clean head-on (0.5→30.5 breaks). The
huge `sog_rmse` ON is a downstream symptom of the extra break/rebirth transients,
not the measurement. Hypothesis to root-cause before any promotion: the
increment-2 velocity covariance (~0.6 m/s 1-σ) is tight relative to the sparse
AIS cadence + the noisier radar-position stream it fuses with, so a PV update
pulls the state and destabilizes subsequent radar gating → misses → M-of-N
deletion. Separately, the anchored scenario is NOT inert (ospa +10.5): the
watch-circle swing SOG peaks ~0.85 m/s, above the 0.5 m/s threshold, so the
anchored vessel intermittently emits velocity — `nav_status`-gated suppression
(force Position2D when nav_status ∈ {1,5}, now that the loader surfaces it) is
the concrete fix candidate. Shared-helper reuse means whatever fix lands applies
to both the NMEA and replay paths.
## 2026-07-06 — D8 R-BAD berthing dataset: feasibility GO (with a regime caveat) [Cl-3 feasibility; no extraction done]

Feasibility-only assessment of the R-BAD dataset (pre-water item 8,
`docs/superpowers/plans/2026-07-02-data-expansion-todos.md` §D8). Verdict:
**GO** — proceed to the D8 next step (extract 1–2 station-hours as fixtures +
a label-scored replay). No extraction performed here; this is a desk check
against the authoritative Zenodo record + the paper abstract. The MDPI paper
full text was bot-blocked (403), so four specifics below are flagged
"confirm-at-extraction" rather than asserted.

**What it is.** "A Comprehensive Radar-Based Berthing-Aid Dataset (R-BAD)",
MDPI *Electronics* 14(20):4065 (2025), doi:10.3390/electronics14204065.
Data on Zenodo record 16936465 (doi:10.5281/zenodo.16936465). 69+ h of
synchronized **FMCW mmWave radar point clouds + video**, collected onboard an
operational Ro-Ro/Passenger ferry across **13 ports**, covering arrivals,
departures, port-idle, and cruising.

**License — commercial: GO.** Zenodo license is **CC-BY-4.0** (confirmed via
the record's API metadata; no NonCommercial clause). Commercial use is
permitted with attribution — the decisive gate for a TKMS product, and the
cleanest possible outcome. (Contrast philos: form-gated, research-scoped.)

**Format vs our model: GO, with a sensor-regime caveat.** Two files:
- `Raw Aggregated Frames Data.zip` (**31.6 GB**): structured radar detections
  as **CSV** paired with synced **MP4** video. CSV detections parse straight
  into the `radar_plots.csv` shape the replay adapters already consume — no
  rosbag/proprietary decode needed (unlike the philos `.bag` or DLR HDF5).
- `Labelled Buffers Data.zip` (**31.2 MB**): annotated radar detections grouped
  into buffers for clustering/tracking/classification ML.

  **The caveat that reframes the dataset:** R-BAD is **automotive-band mmWave
  FMCW radar (60–67 + 77–81 GHz)**, NOT marine X-band. That is a *different
  sensor class* from philos (Navico broadband ~9 GHz) and HAXR (marine radar):
  short berthing-range, dense point clouds, different clutter/multipath. So
  R-BAD corroborates the philos *scene* (piers, moored vessels, near-shore
  structure) on a *new sensor*, NOT a second marine-radar geography. Its
  occupancy/clutter numbers will need fresh characterization; philos/HAXR
  tuning will not transfer. This is the headline: value is a genuinely
  non-AIS-labelled berthing scene + an hours-scale video substrate, not a
  marine-radar transfer test.

**Truth honestly available: GO — two independent routes.** (1) Provided
annotations (the labelled buffers: clustering/tracking/classification labels) —
real non-AIS labelled truth, the exact "false track actually means false" gap
D7/D8 target. (2) Synced MP4 supports an independent manual label pass (the
philos R8 sunset_cruise/close_approach workflow) at hours-scale. Route (2)
sidesteps the circularity risk in route (1): if the provided labels were
radar-derived/self-labelled, scoring the detector against them shares a source
(the standing circularity rule) — so label provenance must be checked before
any accuracy claim, and video-labelling is the clean fallback.

**Download/storage cost: GO.** ~**31.6 GB** total (31.6 GB raw + 31 MB labels)
— smaller than the philos tarball set (~25 GB) or a HAXR hour, trivially
storable. Extracting 1–2 station-hours as fixtures is cheap.

**Confirm-at-extraction (unresolved from metadata + abstract; all live in the
CSV headers / zip README, i.e. the first extraction hour, not a blocker):**
(a) detection CSV columns + coordinate frame (Cartesian x/y vs range/azimuth —
our adapter wants range/azimuth body-frame); (b) annotation schema + label
provenance (classes? track IDs? manual-from-video vs auto?) — the circularity
determinant; (c) own-ship **GPS/ego-pose** presence in the released CSVs
(needed to project body-frame detections to a world/occupancy frame — the
platform is a *moving* ferry, so the ego-motion-smear question, cf. D4/Reeds,
applies, though berthing speeds are low); (d) radar max range + scan rate.

**Net.** GO. License is clean for commercial use, data is accessible + cheap +
CSV-friendly, and honest non-AIS truth exists two ways. The single substantive
caveat is that R-BAD is a *new sensor regime* (mmWave), so it earns its place
as a non-AIS-labelled berthing-scene probe and a video-labelling substrate —
not as a marine-radar tuning confirmation. Recommend it over philos-style
effort only where the berthing-scene labels or hours-scale duration are the
point; keep expectations off direct philos/HAXR number transfer.

Sources: Zenodo record 16936465 (CC-BY-4.0, file sizes, description);
abstract of doi:10.3390/electronics14204065 (mmWave bands, ferry platform,
detection/tracking/classification scope). Paper full text not accessed (403).

## 2026-07-06 — Multi-sensor simulation battery: first controlled fusion accuracy gate [Cl-3]

First fusion-accuracy measurement scored against truth INDEPENDENT of every
sensor by construction (seeded simulation, not AIS-as-truth). Six scenarios,
seed 0, radar+AIS(+camera). Fixtures: `tests/fixtures/sim_multisensor/` (Python
generator, local-only/git-ignored; `--with-simms` bench flag,
`SimMultisensorScenarioRun`). Full table + reproduce commands in
`docs/baselines/2026-07-06_sim_multisensor_battery.md`. GOSPA c=20 p=α=2.
No defaults changed; the sim scenarios are additive and self-skip when fixtures
are absent (bench + suite bit-identical without `--with-simms` / `SIMMS_DIR`).

**Determinism (a deliverable):** trafficgen (COLREG encounter geometry) uses
stdlib `random`, seeded at the wrapper level (`random.seed`); all numpy draws
from per-`(scenario,sensor)` `default_rng([seed,salt])`. Generation is a pure
function of `(scenario,seed)` — byte-identical across processes (verified under
a changed `PYTHONHASHSEED`) and on-disk fixtures reproduce a fresh regen exactly.

**Headline (MHT `imm_cv_ct_mht`, fusion vs radar-only, OSPA m):** fusion beats
radar-only where continuity / absolute position matter — `ais_dropout` 33.1 vs
67.2 (~2×; AIS anchors identity, radar carries the track through the dropout,
lifetime 0.99 / 0.5 id-switches), `headon` 39.9 vs 61.4, `overtaking` 74.5 vs
87.2. Radar-only is slightly better on `crossing` (73.4 vs 89.1) and on the
clutter scenario (127.9 vs 183.8). This is the first controlled
fusion-vs-single-sensor delta the project has.

**Anti-model-matched-optimism bit (by design):** `sim_ms_clutter_burst`
(compound-K clutter, NOT flat Poisson) is the only scenario where BOTH trackers
over-count — MHT `card_err +2.51`, PMBM `+3.48` — because their clutter term
assumes uniform Poisson. Radar-only over-counts less (+0.93) than fusion. This
is the designed discrimination target for the clutter/birth-model campaign: a
spatially-varying-λ model should measurably beat uniform-λ here. The
rudder-rate-limited maneuvers (outside the CV/CT IMM set) cost identity not
position: `overtaking` 12.5 id-switches / 16 breaks, `crossing` 7.3 / 8.3, with
RMSE steady ~25 m.

**ADR-0002 canary:** the radar-silent + AIS-silent camera-only contact in
`sim_ms_anchored_camera` is present in truth throughout and produces camera
bearings, but bearing-only cannot birth a track (corroborate-never-initiate), so
it surfaces as the wedge/hazard channel, not a kinematic track (OSPA ~309 / card
slightly negative reflect the un-localized contact). Never suppressed to nothing.

**#20 note:** the AIS fixtures carry `sog_mps/cog_deg/nav_status`, but
`loadAisCsv` still reads only `time/mmsi/lat/lon` (Position2D) — the sim
scenario-run hits the same SOG/COG-drop gap as the replay loaders. Reported, not
worked around (out of this ticket's scope).

Fixture checksums (sha256 prefix; own / ais / radar / cam / truth):
`sim_ms_headon` a4ecaba3 / 68b0c5d4 / 0dc18133 / b12a6528 / d1cfdbb7;
`sim_ms_crossing` a4ecaba3 / 0a8223d4 / fe0d873a / b12a6528 / 8fb0fb81;
`sim_ms_overtaking` ef3c5a36 / 8e7e4364 / 05d581a5 / b12a6528 / 5dd53cd0;
`sim_ms_ais_dropout` a4ecaba3 / 9e8a4f5c / 6f78d623 / b12a6528 / 43bce1cf;
`sim_ms_clutter_burst` a4ecaba3 / edf43927 / c0513ab2 / b12a6528 / 40b568a0;
`sim_ms_anchored_camera` b96e109f / 8c870b55 / cf193727 / 9b72a5a9 / 091f23e7.
(`b12a6528` = header-only empty camera file; only anchored_camera has real
camera rows. Regenerate: `tests/fixtures/sim_multisensor/README.md`.)

## 2026-07-06 — CORRECTION: `philos_radartruth` is AIS-derived, not independent radar truth [measurement integrity]

Standing correction (an observation too). Since the `philos_radartruth`
truth-source variant shipped (2026-06-24, `docs/superpowers/plans/
2026-06-24-pmbm-philos-cardinality-improvements.md`), it was described in code
and plan as "independent radar-derived truth — kills the AIS circularity." **That
is false.** `tests/fixtures/philos/build_truth.py` (line 20, "a quick analytical
projection") builds `radar_truth.csv` by projecting each **AIS** row's lat/lon
into the radar's `(range_m, azimuth)` frame with `uid = MMSI`. Verified: the 20
`radar_truth` uids are exactly the 20 AIS MMSIs, sampled at the AIS timestamps
(100 % overlap). So `philos_radartruth` is **AIS truth expressed in the radar
frame** — a projection/datum consistency check vs `philos`, NOT independent of
AIS. An AIS-consuming arm scored against it is still circular.

Fix (2026-07-06): corrected the `ReplayScenarioRun.cpp` comment (registration +
`generate()`). **Audit of past load-bearing use → CLEAN.** Every prior mention
is either an A/B *delta* (eval-log 2026-07-02 PDA `philos 63.13→63.08 /
philos_radartruth 67.08→67.04`; 2026-06-29 coverage "philos/philos_radartruth
identical") or an *inertness* check (2026-07-02 land-PDA byte-identical) — both
survive because both arms share the same truth, so independence is irrelevant to
the delta. The R8 entries (2026-07-03) that reason about AIS-truth *limits*
explicitly treat AIS truth as incomplete/bound-only and never cite radartruth as
a de-circularizer. The one independence *claim* was the 2026-06-24 plan's Step 6
hypothesis ("if PMBM's gap vs MHT shrinks under the independent truth, the
regression was AIS penalizing real radar tracks") — that inference was **never**
the basis of the shipped philos diagnosis, which was root-caused instead by the
raw-radar check (2026-07-01, "over-count is static infrastructure") and
single-knob isolation. **Net: no shipped accuracy result was ever load-bearing
on radartruth independence** — the good outcome. Detail:
`docs/baselines/2026-07-06_philos_farcross.md`.

## 2026-07-06 — DATA INTEGRITY: `car_carrier_near` rotated-clip fix + fail-loud extractor guard + R4 chart re-check [measurement integrity]

**The bug (established 2026-07-03, R8.8).** `tests/fixtures/philos/out/
car_carrier_near/` (2020-10-22 bag) had `heading_deg = 0.000` constant and
only **26 own-ship rows over 120 s** (0.22 Hz). `extract_section.py`'s topic
lists were written for the 2022 bags: they matched the 2020 bag's sparse
0.2 Hz `/gnss` decoy for position, found no `Vector3Stamped` heading topic,
and emitted a `0.0` heading placeholder. Every world-projected radar return
from the clip was therefore rotated about own-ship by the true heading
(GPS course ≈ 300°). The bag actually carries dense streams the old lists
missed: `/sensor/gps/fix` (72 Hz NavSatFix), `/filter/positionlla` (59 Hz),
`/filter/quaternion` + `/imu/data` (59 Hz attitude).

**Extractor fix + fail-loud guard.** `extract_section.py` now (a) takes
position from the *single densest* NavSatFix topic present (never a merge,
so a sparse decoy can't dilute a dense source), `/filter/positionlla`
(Vector3Stamped `x=lat,y=lon`) only if no NavSatFix exists; (b) derives
heading from the attitude quaternion `heading = (90 − yaw_ENU) mod 360`
when no direct heading topic exists. The quaternion convention was verified
on `ais_ferry_near`, which carries **both** sources: quaternion-derived
heading equals `/xsens_heading` to **0.2°** (same Xsens filter) and
`/philos/sbg_heading` to **~2.2°** (known SBG/Xsens inter-unit offset).
(c) A guard `ownship_integrity_errors` runs *before any file is written* and
hard-errors — naming the clip and offending series, no placeholder CSV — if
heading has ≤1 distinct value OR row rate < 1 Hz over the clip span. This is
the exact failure class that produced the rotated clip; it is now
impossible to repeat silently. `check_ownship.py --all` runs the same guard
over every existing `out/*/ownship.csv`. **Demonstrated:** guard FAILS
loudly on the stashed broken output (0.217 Hz + constant 0.0, both checks
fire) and PASSES on all seven clips post-fix.

**Re-extraction result.** `car_carrier_near`: **8739 own-ship rows** (72 Hz
from `/sensor/gps/fix` — denser than the ticket's ~7k estimate, which
assumed the 59 Hz positionlla), heading **287.9–304.2°, 2179 distinct**,
consistent with GPS course ≈ 300°. Position source `/sensor/gps/fix`,
heading source `/filter/quaternion (quaternion yaw)` (recorded in
`meta.txt`). AIS = **0 rows** (expected — see AIS note). Projection sanity:
the radar-return centroid world bearing rotates **59.8° → 359.8°** (the
~300° heading, i.e. the corruption undone) and median distance-to-charted-
shore drops **121 m → 50 m** (returns-within-100 m-of-shore 44% → 64%) —
returns now land on the Boston shoreline as near-shore harbour radar must.

Emitted-file sha256 (tracked drift-guard; fixtures are gitignored):
```
ownship.csv 6ee33be5d2a5524261c4d16fe731b67afa2dd5325f1e95abced0a0c4330915a2  (8739 rows)
ais.csv     19899e5e258cb8899be2ea1acee8152bc054169fe7508ad0105bf3c33d22b2be  (0 rows)
meta.txt    d5a2fbba6aaa019fcedac250fc72bddfbbc19ac25e7464bcc8759812177d5248
```
(`radar_plots.csv`, 5117 rows, unchanged — `extract_radar.py` untouched.)

**R4 chart-corroboration re-check** (`charts/philos_chart_coverage.py`,
pools all 7 clips; car_carrier's rotated cells had contaminated it).
Before → after (broken vs corrected car_carrier ownship; PNG regenerated):

| metric | before (broken) | after (corrected) |
|---|---|---|
| occupied 25 m cells | 6620 | 5796 |
| expected fixed-structure cells | 1727 | 1755 |
| obstacles ≤50 m (cells / by-plots) | 51.7% / 48.6% | 58.2% / 52.5% |
| shoreline ≤50 m (cells) | 39.8% | 45.4% |
| UNION ≤50 m (cells / by-plots) | 53.6% / 50.0% | 59.5% / 53.5% |
| UNION ≤75 m (cells / by-plots) | 61.4% / 56.5% | 67.0% / 60.2% |

The rotation had scattered car_carrier's returns into ~824 spurious cells;
correcting concentrates them onto charted structure/shore, so coverage
*rises* across the board. The historical R4 headline "**~49.5% chart-
confirmed structure mass**" (eval-log 2026-07-04 entry, line ~726) was
computed with the contaminated clip and maps to the *before* UNION@50 m
by-plots (50.0%); the corrected figure is **~53.5%**. The qualitative claim
(chart owns the single largest measured target) is unchanged and slightly
strengthened; the 2026-07-04 entry's `~49.5%` is left as the dated record,
superseded by this entry.

**The in-coverage UNKNOWN at (42.3583, −71.0464) SURVIVES** — overturning
the ticket's prior assumption that only `ais_ferry_far` validly supported
it. Under the broken heading it was a weak 2-clip coincidence (1 + 1
instantaneous returns). Under corrected geometry `car_carrier_near`
contributes a **persistent longspan cluster** there: 16 returns within 25 m
spanning **105 s / 121 s (87%)** of the clip (was 9 returns / 40 s). So the
cell now qualifies as an expected fixed-structure cell on car_carrier alone
(longspan) plus the ais_ferry_far return, and remains uncharted + in-
coverage. The correction did not dissolve the UNKNOWN — it firmed it up.
It stays a genuine candidate for the occlusion / satellite-resolution pass.

**Standing AIS note.** The 2020 (`car_carrier_near`) and 2021 (`sunset_
cruise`, prodromos) philos campaigns carry **NO AIS at all** (no receiver
in the bag — `car_carrier_near` ais.csv is empty from 0 N2K sentences).
The AIS-veto's real-data validation must therefore come from **HAXR**, not
philos.

**Suite:** untouched — this is Python fixture tooling + docs only, no C++,
no config struct, no defaults; the C++ test suite and the integration-guide
config-coverage test are unaffected.

## 2026-07-06 — Philos `ais_ferry_far` + `almost_cross` measurement pass (pre-water Tier-2 #10) [Cl-3]

Measurement-only pass on the two released philos clips (held-out duty discharged
on sailboats_busy 2026-07-05). No default touched. Wiring added (both proven
bit-identical when unset): `PHILOS_CLIP` clip selector + `PHILOS_RADAR_ONLY`
radar-only measurement mode (the philos scenario previously fed AIS as
measurements unconditionally, so no honest radar-only arm existed). Configs:
`imm_cv_ct_mht`, `imm_cv_ct_pmbm_coverage_land`, `imm_cv_ct_pmbm_adapt`. Single
seed (replay, deterministic). Full data + tables:
`docs/baselines/2026-07-06_philos_farcross.md` (+ `.csv`).

**Clip facts:** `ais_ferry_far` = 19 s, 1038 radar plots, 40 AIS rows / 20
MMSIs (carries SOG+COG), has `radar_truth`. `almost_cross` = 50 s, 1504 plots,
**0 AIS, no radar_truth, no labels**.

**Arm A — `ais_ferry_far` radar-only vs AIS truth (HONEST; c=20,p=α=2):**
missed-dominated — 19 s is barely a confirmation window. MHT confirms
essentially no matched track (gospa 42.3 is degenerate: loc 0, lifetime 0, card
−7 — under-production dodges the false penalty). PMBM forms tracks (lifetime
0.05–0.10, **pos_rmse 46–54 m**) but gospa 78–82 is dominated by `false`
(4484–5305) — largely radar returns the sparse AIS truth cannot score. Only real
accuracy signal: PMBM's ~46–54 m position error where tracks match. **Weight:
19 s / 40 truth rows = a spot check on an untuned clip, NOT a benchmark.** The
`philos` vs `philos_radartruth` frames agree to projection precision (gospa
identical to 5 s.f.; loc 35.6 vs 38.5) → the two-frames **consistency check
PASSES** (see the correction entry above for why it is a consistency check, not
two truths).

**Arm B — radar+AIS (CIRCULAR → mechanics):** AIS fusion transforms tracking vs
Arm A (MHT lifetime 0→0.42, pos_rmse →25 m; adapt lifetime 0.05→0.53, pos_rmse
54→18.5 m). PMBM philos over-count persists (card +17–18); MHT conservative
(card −1.6); identity stable (id_switch ≈0). **#20 SOG/COG velocity path NOT
exercised**: the replay loader `loadAisCsv` emits `Position2D` only (ignores the
SOG/COG columns present in the fixture); the #20 path lives in `AisAdapter`
(NMEA), not replay. R11 mmsi identity does flow. Wiring `loadAisCsv` to emit
`PositionVelocity2D` is an arbiter change (not bit-identical) — listed, not done.

**Arm C — `almost_cross` (no truth):** bench is truth-driven → 0 metrics on a
truthless clip (tracker runs 4.17 s, unscored). Direct harness (EKF+GNN, fixed
1 s clock, `tests/replay/test_philos_farcross.cpp`): 73 final tracks / 211
unique over 50 s. **ADR-0002 persistence canary PASS** — radar contacts surface
as confirmed tracks and persist to end-of-clip, none suppressed into nothing.
Heavy raw-plot over-count (no clutter suppression in the smoke harness);
mechanics-grade presence, not a cardinality claim. ID-stability/id-switch not
obtainable (no truth).

**Honest one-paragraph takeaway:** on the one philos clip with honest truth
(`ais_ferry_far`, radar-only vs AIS), the tracker's real-data position accuracy
is **~46–54 m (PMBM, where tracks match)** over a 19 s window that is
missed-dominated — a spot check, not a benchmark, and the only such number
before the water test. AIS fusion is what makes tracking work here (Arm B). Two
integrity findings fell out (radartruth is AIS-derived; #20 unreachable via
replay) and are handled above / listed for the arbiter.

Fixture checksums: `ais_ferry_far` ownship 707978cc / ais d743cce5 /
radar_plots 300109a4 / radar_truth 3fdff546; `almost_cross` ownship e78bd603 /
ais b9595f9a (empty) / radar_plots 9e4a3725.

## 2026-07-06 — Perf round 3: hot-path mechanical sympathy — 1.5–1.66× on the PMBM/IMM likelihood path, output preserved [Cl-3]

Branch `hotpath-mech-sympathy` (worktree, off master `3108d0f`). Ticket
`docs/superpowers/plans/2026-07-06-hotpath-mechanical-sympathy-ticket.md`. Full
writeup + pricing: `docs/baselines/2026-07-06_perf_round3.md`. Target: the
round-2 hot bucket (IMM per-mode measurement update), arbiter-verified by
code-read (the `S.determinant()` + `S.inverse()` double-decomposition).

**Shipped (2 commits):** (1) `f7b0914` logLikelihood single-decomposition
(`IEstimator` + `ImmEstimator`) — **byte-identical** (Eigen already LU-decomposes
a dynamic 2×2, so one `PartialPivLU` == `.inverse()`+`.determinant()` bit-for-bit;
verified 0 rows moved on all four gate sets + both haxr workloads). (2) `3fe5d1e`
Class-B package = the parked state-path remainder (`update`/`softUpdate` single
LU) folded with T3 fixed-size 2×2 stack kernels (`gate`/`logLikelihood`
Position2D fast path: H=[I₂|0] selector ⇒ S = P[0:2,0:2]+R on the stack,
closed-form 2×2 score, no heap/matmul/LU per track×meas×mode). New helper
`core/estimation/GaussianScore.hpp`.

**T2 (hoist prediction across measurements): blocked by design, benefit subsumed
by T3.** `PmbmTracker` reaches the estimator only through `IEstimator&`; hoisting
needs a port method, which the pluggable-hot-path invariant forbids (a
predict-once/score-with-R hook would leak the cost-loop's batching into every
estimator). With the 2×2 stack kernels each recompute is a few stack flops, so
avoiding it buys ~nothing. Do not add the port method.

**Numbers (clean Release, warm):** decimated **42.34→28.30 s (1.50×)**, p99
27.9→21.0 / max 35.2→22.9 ms; raw-density **154.2→92.9 s (1.66×)**, p99
123.6→**66.6** / max 137.9→**76.7 ms** — worst-case scan goes from 1.07× to
**1.93×** inside the 148 ms interval.

**Gate-suite pricing (single run on the final package):** philos KEEP (both PMBM
configs) **byte-identical** incl. `lifetime_ratio` (KEEP safety absolute);
dense_clutter_datum 1/1627 moved (one `pos_rmse` @1.17e-6, fp noise);
harbor_complete_truth 25/2686 moved, **all confined to the single non-KEEP config
`imm_cv_ct_pmbm_adapt_k3`** — the known 1e-15 knife-edge birth decision tipping
(`card_err` 9.85→9.375), isolated, not a pattern. haxr primary metrics
(gospa/card/id/ospa/tgospa) unchanged; derived COG/SOG RMSE move at
recursive-filter fp scale. Suite **1050/1050**; no print-pinned test tripped. The
harbor/adapt_k3 knife-edge → improvement-backlog **#21** (benchmark-config
fragility, freeze-rule class).

**Verdict:** campaign-replay goal met (pays for the upcoming clutter/birth-model
campaign's hundreds of replays); the 57 s deployment margin stays with upstream
extraction (round-2 ruling, not gated by this).

## 2026-07-06 — Perf round 2: fresh profile + per-scan latency; no single safe lever left, extraction stays mandatory (batch), but per-scan keeps up [Cl-3]

Branch `perf-round-2` (worktree, off master `ceee0bf`). Ticket
`docs/superpowers/plans/2026-07-06-perf-round2-ticket.md`. Full writeup +
tables: `docs/baselines/2026-07-06_perf_round2.{md,csv}`. Motivation: the Murty
K=1 fix (`45a504d`) removed the old 85 % bucket, so the 2026-07-05 profile is
obsolete. perf unavailable (`perf_event_paranoid=4`, no TTY sudo) → gprof on a
separate `-pg` build; **gprof is bucket-ranking only** (demonstrated ~4–15×
over-attribution of the harness-metrics Hungarian, plus inlining/ICF folding
artifacts — `gate→initiate` and a 140 M/417 M `CoordinatedTurn::~` bucket that
the source does not produce).

**Per-scan latency instrumentation shipped** (bench columns `scan_proc_ms_{mean,
p95,p99,max}` + `scan_interval_s` + `n_scans`; byte-identical, determinism check
extended to skip the wall-derived `scan_proc_ms_*` like `wall_seconds`). Closes
the worst-scan blind spot. **Both workloads keep up scan-by-scan**: dec max
41.1 ms and raw max 101.7 ms both fit inside the 148 ms scan interval (3.6× /
**1.45×** margin). Scan interval, mean/p95/p99/max in the CSV.

**Fresh profile.** Accurate (chrono / with-without): tracker `processBatch` is
94 % (dec) / 90 % (raw) of wall; harness metric scoring is 1.7 % (dec) / **10.3 %
(raw)** — NOT the 27 %/46 % gprof claimed. gprof relative ranking within the
tracker: the **IMM per-mode measurement update** (`gate` + `predictMeasurement`
building `H`, `S=HPHᵀ+R`, `S⁻¹`, `det` via LU/LDLT) is the dominant bucket,
scaling with measurements × Bernoullis × modes; PMBM `bhattacharyya` merge/prune
~2 %; birth ~1 %; **tracker `murtyKBest` is now 1998 calls / a few % — the 85 %
bucket is gone** (of 22 479 total Hungarian calls, 20 481 are the metric harness,
not the tracker). RAW top lever = that IMM measurement-update linear algebra.

**Safe fixes implemented (harness-only, byte-identical):** (1) the latency
instrumentation above; (2) `--fast-metrics` (skip OSPA/GOSPA/T-GOSPA/RMSE/NEES/
NIS scoring) → **raw 163.4→146.5 s (−10.3 %)**, dec within noise; default-off
reproduces baseline metrics exactly. Full suite **1044/1044** green.

**Priced findings (arbiter, NOT implemented):** Position2D `H`-elision
(`H·P·Hᵀ ≡ P.topLeft(2,2)` bit-for-bit; ~5–8 % but blast radius = all estimators,
own ticket); coarse position-box gate prefilter (bigger win but changes gating →
result-affecting); sparse/gated LSAP **deprioritised** (tracker assignment no
longer hot post-fix).

**Verdict (unchanged, refined):** code-only SAFE fixes **cannot** bring raw
under 57 s — the tracker `processBatch` floor alone is ~147 s (needs ~2.6×,
only via result-changing algorithm). **Front-end extraction stays
deployment-MANDATORY for the ≥5× batch-throughput margin gate.** Refinement for
the arbiter: that gate is a *throughput margin*, not a *streaming-feasibility*
bound — per-scan the worst scan fits the interval (1.45×) at raw density, so the
tracker keeps up live without extraction. North-star verdict cell left unchanged
(nuance flagged, not edited).

## 2026-07-06 — D2 GOSPA cross-validation: navtracker == Stone Soup to FP epsilon on one sim + one real run [measurement integrity]

Question: after two truth-fragmentation bugs (autoferry 2026-06-10, harbor
2026-07-02) silently corrupted metrics, does `core/scenario/Gospa.hpp` agree
with an independently-authored GOSPA? Method: export the harness's own
per-scan `(truth, track)` sets — the exact `BenchResult` the metrics consume,
so the cross-check scores identical tracks by construction, not a
reconstruction — and re-score with Dstl Stone Soup's
`stonesoup.metricgenerator.ospametric.GOSPAMetric`. Same convention on both
sides: **c = 20 m, p = 2, α = 2, switching = 0** (α is hardcoded in Stone
Soup's `compute_gospa_metric`; cardinality penalty c^p/α per drop; rooted
distance = (loc+missed+false)^(1/p); decomposition reported pre-root power-p by
both). Tooling: `core/benchmark/GospaExport` + `--export-states-dir` +
`tools/stonesoup_gospa_crosscheck.py` (venv-local, not a Conan dep).

**Result — PASS on both arms:**

| Run | Scans | mean GOSPA (ours / SS) | max per-scan \|Δ\| | card mismatches |
|-----|------:|-----------------------|-------------------|-----------------|
| `harbor_complete_truth` (sim, imm_cv_ct_pmbm, seed 0) | 40 | 49.528608 / 49.528608 | 1.42e-14 | none |
| `philos` (real ARPA replay, imm_cv_ct_pmbm) | 20 | 99.129014 / 99.129014 | 1.42e-14 | none |

Per-scan localisation/missed/false and the recovered n_missed/n_false counts
agree on every scan (philos is the stronger arm: richer cardinality dynamics,
nm 4–14 / nf 38–47 per scan). Max deviation is 1.42e-14 m — pure
floating-point ordering, not an algorithmic difference. **Verdict: the harness
GOSPA is validated by an external implementation under matched conventions.**
The two prior metric bugs were truth *grouping/ordering* faults upstream of the
metric kernel; this closes the remaining question — the kernel itself is
correct. Doc: `docs/algorithms/gospa-crosscheck.md`. Out of scope (parked): a
convention-mismatch audit of Stone Soup's *time-series* GOSPA (switching term)
and running Stone Soup's own trackers as a baseline.

## 2026-07-06 — R8.8 occlusion labelling pass (car_carrier_near): shadow interval MEASURED; R4 UNKNOWN resolved as moored yachts [Cl-3 / ADR 0002]

Operator (user) + analyst video/frame/radar cross-reference on the re-extracted
clip (3855efd). Labels: `tests/fixtures/philos/labels/car_carrier_near_labels.csv`
(committed; same format/discipline as sunset_cruise/close_approach).

**The occlusion archetype is now a measured, labeled case.** The R4 UNKNOWN at
(42.3583, -71.0464) — uncharted, in-coverage, radar-supported across two
clips — is RESOLVED by video: **two moored white motor yachts** (~860 m W of
own-ship track). Present the ENTIRE clip, but radar-silent **t 50-85 s**
(7 consecutive empty 5-s bins) exactly while NYK **GENTLE LEADER** (name read
off the bow on video) crosses that bearing at 150-250 m: returns cease and
resume at the SAME cell. Bonus: the same yachts are CAMERA-hidden behind the
carrier at clip start (center camera until ~20 s / ~36 s) — one clip, two
occlusion modalities (radar LOS + camera LOS).

**What this enables (the R8.8 question):** a coverage-decay LOS/shadow test —
those 35 s of scans must NOT count as observed-empty for the yacht region
(`unknown_w860` row is the assertion target). Whether the decay sector model
needs an explicit LOS guard or shadow-induced false-fires stay negligible is
now decidable against ground truth instead of argument.

**Operator caveat recorded in the labels:** left camera is shaky — objects
repeatedly leave the frame; out-of-frame is "not observed", never
"observed empty" (constraint on any evict_camera_empty-style evidence).

**Residuals:** port-quarter big radar object (210-250 m, t 0-60) not visible
in any camera — labeled radar-only, class unknown, provisional
SUPPRESS_STRUCTURE. Camera-bearing YOLO chain deliberately NOT used for
labelling (circularity: these labels will test camera corroboration); running
it on this clip as a machine-vs-operator comparison is a named follow-up.
R8.8 is now FULLY closed (code half 3855efd + this pass).

## 2026-07-06 — Raw-density (undecimated) realtime check post-Murty-fix: keeps up (2.0×), fails the ≥5× margin gate [Cl-3]

Question: after the Murty fix, is clustering-first decimation still a
deployment-REQUIRED front-end stage, or just an accuracy lever? Workload: the
same kattwyk_08 285 s window UNDECIMATED (169 plots/scan regime), cut from
`kattwyk_08_full.csv` by the decimated fixture's exact tod bounds
[29096.383, 29380.922] → 299 981 rows (1.83× the decimated 163 723; not an
md5-pinned fixture — regenerate with that filter). Same config/invocation as
the probe (`imm_cv_ct_pmbm_coverage_land`, Release build).

**Result: wall 141.4 s for 285 s of data → 2.0× faster than realtime** (peak
RSS 168 MB). Pre-fix this regime was ~20× SLOWER (95 min). So raw density now
*keeps up* in absolute terms but **fails the ≥5× margin gate** (needs ≤57 s).
Cost is superlinear in density as expected (3.4× wall for 1.83× rows — per-scan
cost ~ rows × Bernoullis, and the phantom population grows with density too:
card_err 100.5 vs 48.8 decimated, the known undecimated over-count 2×).

**Verdict: front-end extraction stays deployment-MANDATORY under the margin
standard** — but the failure mode changed from "hopeless" to "margin-short",
so a weaker/cheaper front end than eps-50 clustering could also close it.
Corollary: the extraction stage itself now needs its own realtime budget
measured before deployment (a too-slow preprocessor just moves the lag
upstream). Remaining realtime blind spot (both regimes): per-scan WORST-CASE
latency (max/p99) — replay means hide density-spike stalls; add per-scan
timing columns to the bench next time it's touched.

## 2026-07-06 — Murty K-th-assignment early exit: 515 s → 41.6 s (12.4×), output-identical [Cl-3]

Step 3 of the runtime probe, implemented same-day because the fix is one
guarded `break` in `Murty.cpp` (skip child generation once the K-th assignment
is accepted — children only feed heap pops that never happen; also removes the
per-child full cost-matrix copies). Bit-identical by construction at every K;
the existing Murty tests pin it (K=1 ≡ Hungarian on a 30-trial random batch,
full K=6 enumeration vs brute force). Full suite **1042/1042** green.

**Re-measure** (same workload/invocation as the probe, md5-verified fixture,
main-tree Release build): wall **41.6 s** vs the probe's 515 s RelWithDebInfo
steady-state baseline → **12.4×** (projection was ~6×; the extra factor is
Release-vs-RelWithDebInfo plus the eliminated child cost-matrix copies, which
gprof under-attributed). Peak RSS 93 MB (vs 83 — build-type delta, still a
non-issue). Accuracy **identical to the 6-decimal print**: gospa_mean 104.262 /
card_err_mean 48.7626 / lifetime_ratio 0.104497 / id_switches 0.

**Takeaway:** PMBM+occupancy on the decimated 285 s kattwyk_08 feed now runs
**~6.8× faster than realtime** (was 1.8× *slower*) — the deployment realtime
gate (≥5× margin at 60–100 plots/scan) is met on this workload with room. The
probe's two named follow-ups (sparse/gated LSAP; `--fast-metrics` bench stride)
remain open but are no longer blocking anything; re-profile before spending on
them, since the 85 % bucket is gone and the landscape underneath is unmeasured.

## 2026-07-05 — PMBM runtime probe: profile + knob sweep (measurement only) [Cl-3]

Branch `pmbm-runtime-probe` (worktree). Ticket
`docs/superpowers/plans/2026-07-05-pmbm-runtime-probe-ticket.md`. Motivation:
PMBM wall time throttles dev (increment-8: EKF+GNN 33 s vs PMBM+occupancy on the
decimated `kattwyk_08` 285 s window). MEASUREMENT ONLY — no default touched, no
algorithm changed; the only code is an env-gated compute-knob override block in
`Config.cpp::makePmbmConfig()` (default-unset = bit-identical). Full results +
frontier CSV: `docs/baselines/2026-07-05_pmbm_runtime_frontier.{md,csv}`.

**Baseline** (`imm_cv_ct_pmbm_coverage_land`, decimated `kattwyk_08_dec50_w285`,
md5 `304cdeb8…`, single-threaded, RelWithDebInfo): ~515 s steady-state wall
(cold-start first run 640 s — CPU frequency drift; batches settle to ±0.2 %),
**83 MB peak RSS**, gospa 104.26 / card_err 48.76 / lifetime 0.104 / 0 id-switch.
~1.8× slower than realtime on this decimated feed (the ~20× figure was raw
density). RSS is a non-issue.

**Step 1 (profile, gprof — perf blocked by `perf_event_paranoid=4`, no root):**
the Murty-vs-cost-matrix question is **neither**. `hungarianAssignment` is
**85.2 % of runtime from the tracker's `murtyKBest`** (165 721 of 186 202 solves;
cost-matrix construction ~2.7 %, occupancy layer < 0.1 %). Root cause: a **K=1
inefficiency** in `Murty.cpp:75-116` — the child-generation loop runs one
Hungarian solve per assigned row (**N≈82/scan**) and then exits because
`size==K==1`, discarding every child. ~98.8 % of solves are wasted. A separate
**~10.5 %** of wall is the bench's own per-scan OSPA/GOSPA/TGOSPA assignment
scoring (harness cost, not the tracker).

**Step 2 (knob sweep, OFAT):** the frontier is **flat** — no config knob buys a
fast-dev-grade win, because the dominant cost scales with per-scan
measurement/birth rows, which no knob controls. Best: `r_min = 1e-2` → −5.8 %
haxr / −7.2 % philos, **byte-identical accuracy** on haxr *and* on the gate suite
(harbor_complete_truth, dense_clutter_datum, philos — all unchanged; KEEP-safe by
the OSPA/card/lifetime proxy). `gate`/`max_ppp` in the noise; `trajectory_window`
cold; `max_global_hypotheses` **excluded (inert under K=1**, verified).

**Recommendations.** Fast-dev config: `r_min = 1e-2` for a free ~6 % (marginal;
NOT a fast-dev multiplier — none exists at the config level). Candidate default:
same, gate-green, flagged for the arbiter (should still clear the philos
KEEP-label test + determinism before promotion). **Step 3: strongly FOR** — a
~1-line early-exit before Murty's child loop (`if ((int)out.assignments.size()
== K) break;`) is bit-identical at K=1 and projects ~83× on the dominant bucket,
~515 s → **~70–90 s (~6×)**. The flat frontier is the proof tuning can't reach
it. Determinism + full ctest suite green on the branch with the flag added.

## 2026-07-05 — Held-out pass: sailboats_busy scored against the locked pre-registration [Cl-3]

First frozen-detector held-out validation. Detector frozen as
`imm_cv_ct_pmbm_occupancy_detector` + `membership_exit_factor = 0.6` (hysteresis
ON, deployable artifact); scored against the verbatim pre-registration committed
BEFORE the clip was touched (git-provable ordering). Eight predictions →
**3 HIT (zero AIS; fleet builds no persistent cells / persistent mass is shore
structure; highest raw track mass of any clip — 22 703 track-scans vs
close_approach 15 182 / sunset 18 295), 1 MISS (Longfellow Bridge pillars did not
surface at 550–600 m ENE), 4 PARTIAL (far-bank weak cross-validation; land-prior
unverifiable on an unlabeled held-out clip; committee-boat identification needs
frames; and the valuable one —** prediction 7: the low-bar detector
(`extended_cells_min=1`, `persistence_bar=0.2`) DID transiently bait on the moving
dinghy fleet in open water — a mild instance of the race-mark trap the analyst
pre-flagged as the most-informative failure, amplified because the clip ran 120 s
vs the assumed 20–80 s; nothing matured into sustained extended structure (peak 4
hazards, all high-persistence mass on shore lines). The big falsifier
(persistent EXTENDED structure mid-basin) did NOT fire → projection/registration
and the analyst's philos model are intact. Freeze flip-guard: zero flips (every
prediction is entry-driven; hysteresis is exit-only). Full results table:
`docs/baselines/2026-07-05_heldout_results_sailboats_busy.md`. Probe:
`tests/replay/test_heldout_sailboats_probe.cpp`. `almost_cross` / `ais_ferry_far`
measured, not bet on.

## 2026-07-04 — Increment 8: HAXR occupancy A/B — persistence detector near-inert on a 2nd real geography [Cl-3]

Steady-state occupancy A/B on real Hamburg port radar (HAXR), 3 sites × 08 UTC
hour (Kattwyk / Seemannshöft / Parkhafen — one per site for geographic diversity),
radar-only. **HAXR truth is AIS-only → cross-check, NOT the gate** (harbor_complete_
truth stays the gate). Harness fixes this pass: HaxrScenarioRun now sets a nominal
datum (was missing → occupancy silently never wired: commit e5be99b) + per-station
env params; bench `--config-eq` (commit 5ae6117).

**Decimation (clustering-first, per the compute reality — undecimated PMBM is
1h35m/config, ~172× EKF+GNN).** `extract_plots.py --cluster-eps-m` raised per
site to hit the 60–100 plots/scan band (kattwyk/parkhafen eps=50 → 82/55, dense
seemannshöft eps=85 → 91); merges extended STRUCTURE (the phantom source) while
point targets survive as single plots — NOT amplitude (which would delete the weak
returns = small non-AIS craft we care about). 285 s windows, time-matched AIS
truth, both A/B arms sharing each site's IDENTICAL decimated feed (md5-pinned).
**Direction-of-bias (acknowledged):** decimation removes phantom load from the
baseline, so it UNDERSTATES any occupancy benefit — conservative. (Honest aside:
nobody feeds 169 plots/scan to a production tracker; sensible preprocessing is
deployment-realistic, so the decimated regime is arguably MORE representative.)

**Config correction:** the standard `imm_cv_ct_pmbm_occupancy` and `_sensitive`
classify **occ_peak_structures = 0** on decimated HAXR → inert → A/B byte-identical
to land OFF. The config that ENGAGES is the Stage-1b-ii **`_occupancy_detector`**
(coarse 100 m grid + clutter-adaptive bar; comment: "A/B vs imm_cv_ct_pmbm_land").

**Result (occupancy_detector / _detector_coverage ON vs imm_cv_ct_pmbm_land OFF):**

| site | metric | OFF land | ON det | ON det+cov |
|---|---|---:|---:|---:|
| kattwyk | card_err_mean | 51.037 | 51.033 | **50.670** |
| | gospa_false | 10729.7 | 10728.9 | **10656.4** |
| | occ_peak_structures / suppress_hits | — | 31 / 175 | 26 / **7355** |
| seemannshöft | card_err_mean | 58.218 | 58.201 | **57.982** |
| | occ_peak_structures / suppress_hits | — | 33 / 707 | 33 / 4793 |
| parkhafen | card_err_mean | 35.856 | 35.810 | **35.451** |
| | occ_peak_structures / suppress_hits | — | 17 / 744 | 18 / 2618 |

`lifetime_ratio` and `gospa_missed` are **IDENTICAL** across all arms (real vessels
untouched — the layer is SAFE), and `wall_seconds`/RSS are within run-variance
(no "N× faster" — phantoms barely cut, so the Bernoulli count barely moves).

**Takeaway — the "persistence does not discriminate" wall, confirmed on a 2nd
real geography.** The detector engages (classifies structure, fires up to 7355
suppressions) yet cuts the phantom over-count by **< 1 %** (card_err −0.2…−0.4 of
a 35–58 over-count). The persistent+extended classifier catches piers/structure,
but the phantom over-count is **diffuse harbor clutter** not concentrated in those
cells. Same shape as philos (see [[project_stage1b_occupancy]]). Direction is
correct (ON ≤ OFF, never worse) and safe, but the magnitude is negligible. This
validates the strategic pivot: Stage 1b-ii must be a **corroboration** detector
(AIS/camera — the veto wired in 0472eae), NOT persistence. Coverage-aware decay
(det+cov) accumulates far more suppression (7355 vs 175 hits) for a slightly
larger — still negligible — reduction, consistent with the 6c stale-pin story.

**Robustness — 9 station-hours (3 sites × 08/09/11).** The near-null holds across
geography AND time: det+cov card_err reduction ranges −0.08…−1.23 (0.2–3 % of the
34–60 over-count) on 8 of 9, and is slightly POSITIVE (+0.93) on seemannshöft_09.
**Suppression is decoupled from phantom reduction** — kattwyk_09 fired 10 041
occ_suppress_hits yet cut card_err only 1.18 (≈ 0.0001 card_err per suppression):
the suppressed cells are not the phantom sources. This is the concrete evidence
for "persistence does not discriminate" — the layer suppresses real structure but
the over-count is diffuse clutter elsewhere.

**AIS third arm (veto mechanics on real AIS; 3 sites).** `HAXR_FEED_AIS=1` feeds
the AIS vessel positions as `SensorKind::Ais` measurements (740/site) so the
corroboration veto (observeVesselFix, 0472eae) fires on real traffic. **HARD
CIRCULARITY RULE:** AIS is both input AND truth here → this arm measures veto
MECHANICS only, NEVER accuracy-vs-AIS (scoring against the same data we fed).
Result: the veto is **mechanically LIVE end-to-end on real AIS** — feeding it
shifts occ_suppress_hits materially at every site (e.g. parkhafen det 744→9471)
and ticks structure classification up (occ_peak_structures 31→32, 26→33 kattwyk).
But the effect is **ENTANGLED**: the added AIS tracks feed the occupancy model
more (position, 1−r) data, classifying MORE structure and generating MORE
suppression queries, which swamps the veto's near-AIS suppression-LIFT — so
occ_suppress_hits mostly rises, not falls. lifetime_ratio is mixed (kattwyk
0.1466→0.1485, parkhafen 0.1019→0.1086, but seemannshöft 0.1438→0.1374) and
circular. Net: the wiring is validated on real data (the reviewer's ask), but the
veto's ISOLATED benefit is unmeasurable without a veto-ON/OFF toggle holding AIS
constant (clean follow-up — the always-on veto has no A/B partner today).

**Self-heal target: N/A on HAXR** — self-heal (wrong camera eviction → re-emerge)
is a camera-eviction property (increment ii); HAXR is radar-only, no camera.

**Decimation confound — RESOLVED: not an artifact.** Undecimated kattwyk t40
(169/scan) detcov vs land: card_err 113.14 → 112.63 (**−0.51 = −0.45 %**), vs the
decimated −0.37 = −0.72 %. Undecimated the phantom over-count is ~2× larger (113
vs 51 — confirming the user's direction-of-bias prediction that decimation removes
phantom load from the baseline), and the detector classifies MORE structure
(occ_peak_structures 40 vs 26), yet its effect on the over-count is STILL
negligible (smaller as a fraction, even). So the near-null is real in BOTH
regimes; decimation did not hide a benefit. **Bottom line:** the persistence
occupancy detector is near-inert on real dense-harbor radar across two geographies
(Hamburg HAXR + Boston philos) and two decimation regimes — persistence does not
discriminate the phantom sources. The forward path is corroboration (the veto,
validated mechanically-live on real AIS above), and a fundamentally different
clutter/birth model for the diffuse over-count — NOT persistence tuning.
Harness: commits e5be99b (datum + per-station env), 5ae6117 (--config-eq),
0472eae (veto wiring). Full suite green.

## 2026-07-04 — Suppression veto: production wiring (was inert) [Cl-3]

Review finding (post-R10): the R9 item-1b corroboration veto had a real,
model-side-tested mechanism (`LiveOccupancyModel::observeVesselFix` →
`birthSuppression` carve-out) but **no production feeder** — `observeVesselFix`
was called only from unit tests. `PmbmTracker`, the only production producer,
built the occupancy `observe(bundle)` feed but never extracted the
`isNonScanningSource` (AIS/Cooperative/RemoteTrack) positions to feed the veto.
So in any real run or bench the veto was **inert**, and a header comment
falsely claimed the wiring already selected and fed anchors. This is the same
failure shape as the earlier "clutter map inert in PMBM, observe never called"
(cost weeks once); caught early here because the R10 handoff invited the check.

**Fix (TDD, Option A — port-level, hexagonal-clean).** `ILiveOccupancyFeed`
gains a default-no-op `observeVesselFix(double t_unix, Vector2d position_enu)`
(primitives, so the port stays free of any `core/static` type). `LiveOccupancyModel`
overrides it, delegating to the existing `VesselFix` overload. `PmbmTracker`'s
occupancy producer collects `isNonScanningSource` positional fixes in the same
scan loop that already tests that predicate for coverage exclusion, and routes
them via `observeVesselFix` just before `observe(bundle)` — only when an
occupancy sink is wired, so unwired runs stay **bit-identical**. The false
header comment is corrected to name the producer.

**Verification.** RED→GREEN: a new wiring test proves an AIS fix reaches both a
`SpyOccupancyFeed` and a real `LiveOccupancyModel::vesselFixCount()` **through
`processBatch`** (not a direct model call), and a scanning-radar return does
NOT feed the veto. 117-test occupancy/philos/churn/determinism/clutter subset
green (the now-active veto shifts no gate: philos is zero-AIS, the synthetic
structure gates are radar-only, and the veto only ever LOWERS suppression —
conservation-safe). Full suite green. Real-data validation of the veto's
EFFECT rides increment 8 (HAXR hours carry AIS channels; philos does not).

## 2026-07-04 — R10: remote-track ingestion (shore/VTS pseudo-measurements) [Cl-3]

Closes the last gap in the target deployment suite (remote station sends TRACKS).
Stance = design spec §13: another tracker's output is a **pseudo-measurement**,
never an independent observation. All TDD; full suite green (see below).

**Shipped.** (1) `SensorKind::RemoteTrack` appended (last enumerator; serialized
values unshifted) + folded into `isNonScanningSource` (excluded from cov_sensor
self-estimation like AIS/Cooperative — a filtered track is not a swept arc). (2)
`RemoteTrackAdapter` (`adapters/remote_track/`): report → ENU `Position2D`
(`PositionVelocity2D` when velocity opt-in, default OFF/extra-suspicious), with
R-inflation (×3 default on stated covariance; 50 m pessimistic default when none
stated — never both), rate thinning (1 update / 2 s per `(source_id,
remote_track_id)`), `sensor_track_id`+`mmsi` hints, and a `circularAisMmsis()`
guard that surfaces MMSIs double-counted across a raw-AIS + AIS-fusing-shore
wiring. 12 adapter unit tests. (3) Latent hazard fixed fail-loud: `SkewProfile`
per-kind array was sized `8` (== old enumerator count) and indexed by `[]`; a 9th
kind was silent OOB. Now sized `9` + bounds-checked `.at()` (R8.8 lesson — throw,
don't corrupt). (4) Config guard (front of R10) already shipped in the prior pass.

**Fusion scenario (the acceptance test).** `PmbmRemoteTrackFusion`: remote +
radar + AIS + cooperative on ONE vessel, remote driven through the real adapter
(dogfooded), miss model `use_sensor_activity` alone (guard-compliant). Asserts:
ONE confirmed track (no dual from the remote feed); the RemoteTrack touch is on
its provenance (remote fused in, not spawned); **ID stable across a remote
id-swap** (100→200 — external id is a hint, invariant 5); ID stable across a
remote **dropout** while radar corroborates (R9-style no-retirement).

**NEES sanity (the R-inflation tripwire), recorded:** mean position NEES =
**1.79** over 46 samples (2 DOF, ideal E[NEES]=2). The ×3-inflated remote channel
fused with a truthful radar leaves the estimate **consistent, not overconfident**
— R-inflation is sufficient at this scenario's fidelity. This is the detector for
"inflation stopped being enough" (→ covariance intersection, deferred per §13):
if this NEES climbs well above 2 on a real feed, revisit. Definitionally distinct
from a gate — recorded as a consistency observation.

**Debugging note (honest).** First cut of the fusion test made TWO confirmed
tracks for one vessel — a moving target + noise seeding a second cross-hypothesis
Bernoulli. Root cause was my *stripped test config* (bare `adaptive_birth`, no
smart-birth-skip), not the tracker: the production recipe uses
`measurement_driven_birth` + `smart_birth_skip_existing` (Reuter 2014 — don't
birth at a measurement an existing high-r Bernoulli already explains). Aligning
the test config to the real recipe (not tuning a threshold to pass) collapsed it
to one track. Lesson logged: fusion scenario configs must be
production-representative, not minimal.

## 2026-07-04 — Corroboration veto + R9 cooperative+radar readiness (one pass) [Cl-3]

Packaged together because they share a seam (the `SensorKind` non-scanning
predicate and the cooperative/AIS discriminator). Four pieces, all TDD:

1. **Suppression VETO (R9 item 1b) — the fourth corroboration source.**
   `LiveOccupancyModel::observeVesselFix` + `veto_radius_m` (100 m) /
   `veto_window_s` (60 s). A birth is NEVER suppressed within veto_radius of a
   RECENT AIS/cooperative vessel fix — the strongest vessel discriminator under
   the ADR-0002 amendment ("where we CAN tell, a vessel must track"). The veto is
   LOCAL (the rest of a structure still suppresses), only lowers suppression to 0
   (conservation invariant preserved), and lapses when the feed goes quiet
   (fix pruned past the window → accepted static-hazard degraded mode until the
   next fix). The wiring selects positional anchors (`isNonScanningSource`) and
   feeds only those, so the model stays sensor-kind agnostic. 3 unit tests
   (local carve-out, stale-prune-lapse, distant-no-veto), each non-vacuous
   (suppression >0 before the fix, ==0 after) and confirmed by flipping the veto
   off → RED. Real-data validation rides with increment 8 on HAXR (philos is
   zero-AIS — nothing to measure).

2. **cov_sensor exclusion (R9 item 1a).** `isNonScanningSource` (Ids.hpp; AIS +
   Cooperative, RemoteTrack joins at R10) now excludes non-scanning sources from
   `PmbmTracker`'s coverage-sector self-estimation. A cooperative fix is a vessel
   POSITION, not a swept arc; a self-estimated "wedge" from it, unioned into the
   occupancy decay footprint, over-claims coverage (decay over cells nothing
   observed — the unsafe direction, same family as the multi-cluster bug). Unit
   test: cooperative bundle → no coverage sector, radar bundle → still covered.
   Exposure was latent (needs occupancy detector + coverage flag both on).

3. **Self-healing (increment-ii caveat 2, now a gate).** A WRONG camera eviction
   of a still-present, radar-visible object is a bounded latency window, not a
   hole: suppression lifts (birth-eligible) AND the continuing radar returns
   re-accrue persistence so the hazard re-emerges within ≤5 scans. Over-eviction
   converts a present object to track-eligible or re-hazards it — never invisible.
   Converts caveat (2) from "needs Layer-2" to "bounded today".

4. **Cooperative + radar fusion scenario (R9 item 2) — the coverage gap.** Nothing
   fused these two channels end-to-end (every other cooperative test seeds
   Bernoullis directly). New `PmbmCooperativeRadar` test: alternating coop+radar
   on one vessel → (a) ONE confirmed track, (b) platform_id carried on provenance,
   (c) ID STABLE through a 35 s cooperative dropout (> the 20 s
   cooperative_stale_timeout) because radar corroborates — pinned with an in-phase
   empty scan showing the miss lands in the surveillance branch, not the
   cooperative-timeout branch, (d) retirement once BOTH channels go silent.
   **FINDING (interaction the review didn't flag):** `source_aware_misdetection`
   and `use_sensor_activity` are ALTERNATIVE miss models — combined, the identity
   gate short-circuits an empty scan as "not observable" (no matching platform_id)
   BEFORE the activity model runs, blocking BOTH the surveillance miss and the
   cooperative retirement (a source-aware cooperative track would then never
   retire). The deployment config is `use_sensor_activity` alone (R9 item 3's
   real-test recipe); the test uses that.

**Follow-up (2026-07-04, folded into the front of R10): the gotcha is now
IMPOSSIBLE, not documented.** A documented gotcha rots; the failure it hides is a
silently-immortal cooperative track (errs safe, but a permanent phantom vessel
teaches operators to distrust the display). Following the R8.8 refuse-bad-input
lesson, the `PmbmTracker` constructor now THROWS `std::invalid_argument` when both
flags are set, naming the reason and the recipe (2 guard tests: reject-both /
accept-either-alone). **The guard surfaced a real latent bug it was meant to
catch:** `imm_cv_ct_pmbm_coverage` and `imm_cv_ct_pmbm_coverage_land` were
themselves setting BOTH — they inherit `source_aware_misdetection=true` from
`makePmbmConfig()` and add `use_sensor_activity=true`, so the inherited identity
gate was silently defeating the cooperative stale-timeout retirement their OWN
comment demands ("cooperative/AIS-only tracks must be retired by stale timeout or
cardinality grows"). Fixed both to `use_sensor_activity` alone; the coverage A/B
gate (`SyntheticClutterAB.LandModelRemovesShoreOverCountKeepsRealTargets`) stays
green. If someone genuinely needs both composed, the constructor is where they now
discover the short-circuit and fix the composition consciously.

**Baseline-contamination check (2026-07-04, due diligence): NO recorded baseline
was contaminated.** The defeated retirement can only change output where a
`coverage*` config met an identity-known (cooperative/AIS) track whose feed goes
silent long enough to trip the stale timeout. Auditing every `imm_cv_ct_pmbm_
coverage[_land]` row in this log: (1) the philos real-replay rows are zero-AIS /
zero-cooperative, so the identity gate never engages and no retirement is ever
attempted; (2) every synthetic scenario baselined under these configs
(`shore_clutter_open/nearshore`, the geometry breadth set) runs ≤ 60 s
(`linearSeconds(1,40)`, convoy 60 s), but `cooperative_stale_timeout_sec = 120`,
so the retirement branch is **unreachable within the scenario horizon** — the
flag combination cannot alter the output. The 2026-06-30 and 2026-07-02 coverage
numbers therefore stand as recorded; no re-baseline or annotation needed.

**Deferred:** R9 item 3 (integration-guide cooperative-channel section) folds into
the in-flight doc pass (the review already routes it there). Full suite green.

## 2026-07-04 — Stage 1b-ii increment 6: camera corroboration (ii) — eviction as BEHAVIOUR [Cl-3]

Increment (i) LABELLED a camera-observed-empty cell; increment (ii) makes it act.
New `LiveOccupancyParams.evict_camera_empty` (default false) + `camera_empty_
recency_window_s` (default 5 s). Eviction is a pre-pass in `observe()`: a structure
cell whose per-cell observed-empty streak is matured (≥ sustain) AND recent (last
frame within the window of the scan time) AND whose component is chart-UNconfirmed
has its persistence **spent (erased)**, not merely its hazard dropped. The erase is
load-bearing: coverage-aware decay FREEZES an unobserved departed pin (returns cease
while the cell is outside the swept sector), so dropping only the hazard lets the
frozen persistence re-emit it next scan — a blinker. Evidence is keyed by CELL and
accrues while the cell is off-stage, so eviction fires the instant a flickering cell
re-enters (fixing the increment-i loiterer coincidence). Evidence precedence:
chart-confirmed → held regardless of camera. Conservation-safe **by construction**:
suppression is re-derived from the post-eviction hazard set, so lifting it can only
free a birth, never orphan one. (Refactor: extracted `structureComponents()`, shared
by recompute + the eviction pre-pass.)

**Synthetic PROMOTION GATE** (`test_live_occupancy_model.cpp`; correctness lives
here, per the circularity rule — the philos clips have no truth). 6 eviction unit
tests (departed-evicts + no-blink, chart-held, keyed-by-cell fires on re-entry,
recency ignores stale, off-is-inert, blind-region-spared) plus 2 scenario gates:
- `EvictionSceneDepartedEvictsHeldStructuresStayFlat` — three co-present frozen
  structures (departed/uncharted, chart-held, camera-blind), eviction A/B. Departed
  suppression → **exactly 0** (departed-evicts + conservation); both held structures
  **byte-identical** on vs off (= *tracks_on_keep flat*, and proves no cross-talk).
- `CameraEvictionSurvivesAdaptiveBarFlicker` — the loiterer pathology as a
  DETERMINISTIC regression: a frozen pin blinks out of the structure set as the
  clutter-adaptive bar rises with the live-cell median, matures its streak
  off-stage, and is evicted on re-entry (proven non-vacuous — flipping the flag off
  makes the pin re-emerge when the bar falls → RED).

**Real-data DEMO** (sunset_cruise, coverage+chart+camera, eviction A/B;
`test_philos_occupancy_coverage_6c.cpp`). Total hazard-scans **8114 → 7722** (−392,
−4.8 %). Per region (before/after the departure time):
- `ferry_v1_a` (the ferry's OUTBOUND berth, vacated after its t≈98 move): **after
  t98 180 → 42** — the clean departed-evicts (a real vessel that moved, its vacated
  berth camera-observed-empty). The robust demo.
- `loiterer_v2`: **before t100 121 → 121** (retained — the vessel is still present,
  the camera sees detections at its bearing, the streak resets, so it is correctly
  NOT evicted); after t100 1 → 0.
- `astern_blob` (chart-confirmed, 16 m): **31 → 31** held (evidence precedence).

**Honest caveats (Layer-2 / truth questions, recorded not hidden):**
1. The loiterer is NOT the real-data eviction demo. In this config it is not a
   persistent post-departure phantom — the adaptive bar fades it (off has just 1
   hazard-scan after t100), so there is essentially nothing to evict there. Its
   pathology (frozen pin flickering under the adaptive bar) is proven on the
   SYNTHETIC flicker gate instead. This corrects the increment-(i) framing that
   the loiterer's 1/122 flag was a coincidence to be fixed — 121/122 of its
   hazard-scans are *before* departure, where non-eviction is correct.
2. Eviction also removed ~145 `ferry_v1_a` hazards BEFORE the move (t<98, 358 → 213),
   where the camera intermittently saw the docked berth empty for ≥ sustain. Whether
   that is correct (the ferry is tracked elsewhere / the berth pin is already
   phantom) or over-eviction of a present-but-unseen vessel needs kinematic truth —
   a Layer-2 measurement. The 2 s sustain guards single misses, not a multi-second
   detection gap on a docked vessel.

**Deferred:** no bench `Config` arm — the bench Sweep does not feed camera to the
occupancy model (observeCamera is wired only in the replay harness), so a bench
evict arm would be inert; it lands when camera enters the Sweep for the Layer-2
HAXR-hours A/B (increment 8). Backlog (own small fix): a frozen cell blinking in/out
of the structure set as the adaptive-bar median moves = hazards blinking in operator
output regardless of camera → fix with hysteresis on structure-set membership
(enter/exit thresholds, the CpaEvaluator pattern). Full suite green.

## 2026-07-04 — Stage 1b-ii increment 6: camera corroboration (i) — observed-empty flags vacated cells radar+chart could not resolve [Cl-3]

The second corroboration source (increment 6, label-only stage), and the one that
supplies the AFFIRMATIVE "it's gone" verdict radar and chart cannot. Uses the
camera bearing fixtures (commit 2f0261c). `LiveOccupancyModel::observeCamera`
consumes live camera frames through a dedicated API (NOT the clutter feed —
bearing-only measurements cannot pollute the occupancy/coverage path) and
advances a per-cell observed-empty streak: a cell IN the frame's FOV with no
detection within tolerance of its bearing extends the streak; a matching
detection resets it; a cell OUT of the FOV is untouched (unobserved ≠ evidence of
absence — the coverage-aware-decay principle in the camera modality). A hazard
whose centroid cell has been observed-empty ≥ `camera_empty_sustain_s` (2 s) is
flagged. Label only; inert until fed (the 13 pre-existing model tests stay green).
TDD'd (3 model unit tests: sustained-empty→flag, detection-at-bearing→reset,
out-of-FOV→never).

**FOV gate FIRST (2026-07-03 steer — "before designing anything").** Geometry vs
`sunset_cruise` ownship: the loiterer cell's hull-relative bearing is −12° to
−18° throughout the post-t94 window — **100% (1537/1537) inside the center
camera's ~±22° FOV**, so the camera IS looking (unlike chart on the Charles
basin). Empirically its bearing goes clean: center detections within ±10° of the
loiterer bearing drop 1568 (pre-t94) → 90 (post), and all 90 are in t94–99.5 (the
vessel lingering ~5 s in-frame after its radar returns cease); **t100–120 is 0
detections over 20 s** while other objects (the +20–25° cluster) keep the frame
live. The ferry does not mask it (it swings to −72°, exiting into the left
camera). Gate PASSES: camera corroboration is viable on this clip.

**Result (coverage detector + chart + camera, 1 replay).** Camera-observed-empty
per region (hazard-scans → camera-empty): `ferry_v1_a` (the ferry's OUTBOUND
berth, vacated after its t≈98 move to ferry_v1_b) **538 → 41** — the clean
demonstration: a real vessel that moved, its stale pin correctly marked departed;
`loiterer_v2` **122 → 1** (flagged at t118); `astern_blob` (out of the center
FOV) **31 → 0** — correctly never flagged (unobserved, held by chart 31/31
instead). Every camera-flagged cell is chart-UNconfirmed → the eviction
candidates.

**Honest caveat on the loiterer (its bearing IS cleanly empty — the low count is
not a camera limit).** The loiterer's camera-empty count is 1, not the many
expected, because its *hazard* is intermittent after departure: coverage-aware
decay freezes its persistence (radar never re-sweeps it, 0/283), but the detector's
adaptive bar (median-of-live-cells) flickers the frozen cell in and out of the
structure set, so the hazard rarely coexists with the matured 2 s empty-streak
(it does at t118 → flagged). The camera signal itself is clean (0 detections in
±10° for 20 s); the vacated ferry berth, whose held cell stays a stable hazard,
is the robust demonstration of the identical mechanism. Increment (ii) eviction
will consume these labels; its clean demonstration + promotion gate go on a
SYNTHETIC scenario (departing static object + persistent structure + bearing
sensor), per the circularity rule — the loiterer/ferry are the real-data demo,
not the gate.

## 2026-07-04 — Stage 1b-ii increment 6: chart corroboration — confirms structure, flags departed vessels, on real philos [Cl-3]

The first corroboration source (2026-07-03 queue steer: chart before AIS, because
chart owns the single largest measured target — R4's ~49.5% chart-confirmed
structure mass — with S-57/ENC material already in-tree). `LiveOccupancyModel`
gains an optional charted-structure input (`setChartedStructure`): each emitted
live hazard whose centroid lies within `chart_corroboration_radius_m` (default
100 m ≈ one coarse cell) of a charted structure point is CONFIRMED. **Label
only** — suppression/hazards/tracks are unchanged; the label feeds operator
confidence and the increment-8 eviction-by-evidence policy. Inert-by-default (no
charts set ⇒ all uncorroborated, bit-identical — the 13 pre-existing model tests
stay green). TDD'd (3 model unit tests: coincident→confirmed, distant→not,
no-charts→inert).

**Chart source.** `charts/export_philos_chart_structure.py` densifies
`charts/geojson/radar_clutter.geojson` (the curated, WATLEV-filtered radar-visible
layer) to 8 m Point features scoped to the philos bbox → `tests/fixtures/philos/
charts/radar_structure_points.geojson` (15 974 points). The loader is Point-only
but piers/wharves are LineString/Polygon, so densification is required (mirrors
the R4 script). radar_clutter is the physically-apt SINGLE layer for corroboration
(R4's dual-layer fixed_surface AND radar_clutter agreement was a conservative
DELETION bound; CONFIRMING a classification needs only the radar-visible layer).

**sunset_cruise (coverage detector + chart, 1 replay):** **6220 / 8114 hazard-scans
(76.7%) chart-corroborated.** Per region (hazard-scans → corroborated):
`astern_blob` (large real structure) **31 → 31 (100%)**, nearest charted
structure 16 m; `loiterer_v2` (departed vessel) **122 → 0**, nearest 134 m;
`ferry_v1_a` (real moving vessel) **538 → 0**; `ranks_84_95` (UNKNOWN region)
**955 → 0**. This is the discriminator radar + coverage-aware decay could NOT
provide (6c: the loiterer's cell swept 0/283 after t94): **chart ABSENCE cleanly
separates confirmed structure (retain, high-confidence suppression) from
uncorroborated pins (the departed loiterer, the ferry, the UNKNOWN group — all
eviction / camera candidates).** The 76.7% confirmed fraction says most of what
the detector emits as structure genuinely IS charted structure.

**close_approach (Charles basin) — chart correctly ABSTAINS.** The two KEEP_MIXED
regions are 432 m (`sailing_dock`) and 277 m (`far_bank_line`) from the nearest
charted structure: the sailing-basin infrastructure is FLOATING (docks, moored
dinghies), not in the radar-fixed layer, so chart corroboration confirms nothing
there — correctly, not a miss. **Chart corroboration's reach is exactly where
charts hold fixed structure (inner harbour); the Charles-basin KEEP_MIXED needs
camera/AIS.** (Consistent with the loiterer: camera is the queued next source, and
sunset_cruise now has validated centre-camera bearing fixtures.)

**Verdict:** chart corroboration works and is the first evidence source that can
drive eviction-by-evidence (increment 8's preferred fix over a time floor): a
live hazard confirmed by chart is retained; an uncorroborated pin (loiterer,
ferry) is the eviction candidate. Next: camera corroboration (loiterer as first
target), then the eviction policy that consumes these labels. Full suite green.

## 2026-07-03 — Stage 1b-ii increment 6c: coverage-aware vs universal decay, validated on real philos (`sunset_cruise`, `close_approach`) [Cl-3]

The coverage-aware decay mechanism (6a model + 6b producer + multi-cluster
guard) run on real philos for the first time. A/B is a single-flag swap:
`imm_cv_ct_pmbm_occupancy_detector_coverage` (`estimate_coverage_sector = true`)
vs `imm_cv_ct_pmbm_occupancy_detector` (universal decay). New instrumentation:
`tests/replay/PhilosLabelReplay.hpp` extended **additively** to capture the
emitted hazard set per scan and the coverage sectors the feed actually decayed
against (the existing land-config label tests stay bit-identical — sunset
1633/3070/18295, close_approach 5570/0/15182 — proving the extension inert on
the track-only path). Tests: `tests/replay/test_philos_occupancy_coverage_6c.cpp`
(2 tests).

**The sector mechanism bites — not inert.** On `sunset_cruise` the producer
self-estimated **1328 valid sectors, median 12.6°** (min 10.0°, max 46.8°),
**zero** collapsing to full circle. The 12.6° median is padding-dominated
(≈2.6° raw sweep + the conservative 2×5° `az_pad`), consistent with the raw
per-burst span (~3°) measured 2026-07-03. The self-estimated sector never goes
degenerate on real radar, so the coverage gate is live everywhere.

**`sunset_cruise` — structure presence: coverage-aware materially better.**
Scans on which a hazard covers each region (universal → coverage):
`astern_blob` (large real structure out of camera FOV, rarely swept as own-ship
departs) **9 → 31**; hazards/scan max **4 → 14**, final **0 → 11**. Universal
decay forgets *everything* by clip end; coverage-aware holds genuine off-beam
structure ~3.4× longer. This is a **structural invariant**, not a lucky number:
coverage-aware decays a cell only when observed empty — a subset of the scans
universal decays it — so per-cell persistence is pointwise ≥ universal, the
hazard set is a superset, and presence is held ≥ as long over *every* region
(asserted across all labels).

**`sunset_cruise` — the loiterer is NOT resolved-as-departed by radar alone, and
that is correct, not a bug.** `loiterer_v2` (returns cease t≈94 while in *camera*
view) stays pinned as a hazard to clip end (118 s) under coverage-aware, vs never
pinned under universal. The label optimistically predicted coverage-aware would
"resolve this as a departed vessel" — the measurement shows the opposite, and the
observability probe explains why: after t94 the loiterer's cell is swept in
**0 of 283 scans**. Its departure is a *camera* fact ("final frame empty");
to the radar the cell simply left the swept sector, indistinguishable from
"still there, unobserved". Coverage-aware correctly refuses to decay an
unobserved cell (that IS the mechanism's contract); universal only drops it as a
side effect of dropping all structure. **No radar-only decay policy can resolve
this** — it is exactly the corroboration wall (R4): persistence/coverage cannot
discriminate a departed-out-of-coverage vessel from held structure; only
AIS/camera/chart can. (Presence-safe: a lingering *hazard* is conserved output,
ADR-0002's acceptable degraded mode, not a suppression-into-nothing.)

**`close_approach` — KEEP_MIXED presence held/improved under the suppressor.**
Presence = track OR the region inside some emitted hazard's keep-clear ring
(the ADR-0002 conservation-correct test; a co-located-centre test under-counts
because a suppressed birth's covering hazard may be a large off-region
structure). Fraction of active scans with presence (land → detector-universal →
detector-coverage): `sailing_dock` 0.964 → 0.965 → **0.998**; `far_bank_line`
0.494 → 0.494 → **0.616**. The detector never drops KEEP_MIXED presence below the
land baseline (no object suppressed into nothing); coverage-aware backfills
durable keep-clear zones exactly where the intermittent far-bank craft lose their
tracks at range.

**Verdict: coverage-aware decay is validated on real data — kept.** It is not
inert, it is epistemically correct (decays only observed-empty cells), and it
improves both structure-hazard and KEEP_MIXED presence with zero conservation
loss. **Limit surfaced (drives the next steps):** a vessel that departs by
*leaving radar coverage* lingers as a conserved hazard — only AIS/camera/chart
corroboration cuts that latency → motivates the next increment-6 units (AIS veto,
then chart corroboration). **Follow-up risk for Layer-2 (increment 8):** on
hour-long runs, permanently-unobserved cells never decay (no observed-empty
evidence ever arrives), so stale pins could accumulate; a slow unobserved-decay
floor or corroboration-driven eviction is needed before HAXR-hours steady-state
relies on this. New config asserted to differ from the universal arm in the
coverage flag alone (`Config.OccupancyDetectorArmsDifferOnlyInCoverageFlag`).

## 2026-07-03 — R8.6: `close_approach` KEEP-stress benchmark (KEEP_MIXED labels, densest clip) + R4 ceiling correction [Cl-3]

Second operator video pass (Charles River sailing basin, regatta-density
dinghies). Added the `KEEP_MIXED` existence-label class (`core/benchmark/
ExistenceLabel`): a region holding vessels AND structure, **presence-gated** — a
confirmed track OR an emitted static hazard satisfies; a departure from the
region must become a track. (The current harness scores confirmed TRACKS only,
which is complete under the non-suppressing baseline config below — it emits no
hazards; the OR-hazard branch is exercised when a suppressor config is first
scored on this clip.) New fixture `tests/fixtures/philos/labels/
close_approach_labels.csv` (2 regions, both KEEP_MIXED, video-verified):
`sailing_dock` (R4 ranks 1–2, 42.35853 N/−71.08768 E, r70 — float/dock lined
with ~25 berthed dinghies + 3–4 crewed dinghies sailing beside it, right camera
t≈5 s) and `far_bank_line` (ex-UNKNOWN shore group, 42.3570 N/−71.0837 E, r80 —
far-bank small-craft line, cells persistent across recording days ⇒ fixed
floats/moorings).

The label-scored replay harness is now shared (`tests/replay/
PhilosLabelReplay.hpp`): `runClip(clip, config)` + `decompose(run, labels)`,
used by both sunset_cruise and close_approach. The sunset_cruise numbers are
bit-identical after the extraction (1633 / 3070 / 18295; canaries 0.17/0.47/1.2/
3.6 m; stop→go id 13 @ 2.89 m/s) — the refactor changed no behaviour.

**close_approach KEEP-stress baseline (imm_cv_ct_pmbm_land, 880 scans,
`tests/replay/test_philos_close_approach_labels.cpp`):** `tracks_on_keep = 5570`
(densest clip), `false_on_suppress = 0` (no SUPPRESS region labelled),
`false_unlabeled = 15182`. Per-region coverage (fraction of active scans holding
a confirmed track within radius): `sailing_dock` **0.96** (a track sits 0.14 m
off the label centre), `far_bank_line` **0.49** — the far bank is a distant,
med-confidence float/mooring line, honestly intermittent at range (a track sits
1.40 m off it when present). This clip is the standing **KEEP-stress benchmark**.
The always-on gates are deliberately loose regression guards: a catastrophic-drop
floor on `tracks_on_keep` and a per-region coverage floor at **70% of each
region's own baseline** (so a config eroding a region's real-craft coverage by
>30% relative trips it, without punishing the far bank's honest range-limited
intermittency). The *flatness* judgement — a suppressor's `tracks_on_keep` vs
this land baseline — is the increment-6 A/B, not a fixed threshold here. (Note: a
whole-clip existential "any track ever grazed the region" would be satisfied ~6×
per scan for free in this density and could not tell a real dinghy from a
phantom, so the gate is the per-scan coverage fraction, not mere presence.)

**R4 ceiling correction (item 5).** R4 (below) classified the philos over-count
as ~49.5% SUPPRESS_CHARTED (deletable), ~32.5% KEEP_INCOV_UNCHARTED with the
42.3585 N anchorage "the largest single driver", and 14.2% UNKNOWN "chart silent,
defaults to KEEP, needs a visual pass". This video pass advances that visual pass
for close_approach: the largest KEEP driver (`sailing_dock` = R4 ranks 1–2) is
now **directly frame-confirmed** — right camera t≈5 s shows a float/dock lined
with ~25 berthed dinghies + crewed dinghies sailing beside it → KEEP_MIXED,
high confidence. The **single largest in-coverage ex-UNKNOWN group on this clip**
(`far_bank_line`) resolves toward KEEP as **uncharted floats/moorings/small-craft**
(med confidence: an end-of-clip frame shows a far-bank small-craft line in that
bearing and the cells persist across recording days ⇒ fixed; satellite pending
for the dock-vs-moorings split) — either way a presence-gated KEEP_MIXED region,
not delete-suppressible.

This **corroborates** R4's ≤49.5% deletable ceiling with direct video evidence;
it does not *lower* the number — 49.5% was already R4's conservative deletable
bound (only SUPPRESS_CHARTED). What R8.6 rules out is the *upside*: the hope that
some of the 14.2% UNKNOWN slice hid additional suppressible structure is closed
for this clip's largest in-coverage UNKNOWN group (it resolves toward KEEP). The
remaining UNKNOWN — the out-of-coverage groups and other clips — is still
unresolved. Any philos suppressor exceeding ~50% removal deletes real craft, now
with direct frame evidence for this region, not chart distance alone.

**Deferred (independent, do not gate the coverage-aware-decay work):** R8.6 item
2 (real-data CPA/collision fixture on the t≈61 s dinghy contact) + item 3 (the
15 m plot-floor sensor-doc note) trail as a separate task. The chart-derived
anchorage canaries for `almost_cross`/`sailboats_busy` are also deferred: the
anchorage sits 200–800 m off each clip's own-ship track and I have not confirmed
it is in their radar/camera FOV — asserting an unverified KEEP region would be a
fake gate. They get labels when their own video pass lands.

## 2026-07-03 — R8: video-derived existence labels + label-aware philos decomposition + binary gates on sunset_cruise [Cl-3]

Built the "exam before the student" (the measurement surface the increment-6
corroboration layer is judged against). The `sunset_cruise` clip has **zero AIS**
and no radar-truth, so there is no kinematic truth — the only evaluation surface
is the 2026-07-03 video pass's region labels (`tests/fixtures/philos/labels/
sunset_cruise_labels.csv`, loaded by `core/benchmark/ExistenceLabel`). Labels are
existence/region truth, NEVER converted to `TruthSample`s (would be circular +
corrupt GOSPA localisation). Ran the clip through `imm_cv_ct_pmbm_land`
(`tests/replay/test_philos_sunset_labels.cpp`), 1328 scans.

**R8.2 decomposition (confirmed track-scans, land, no suppression):**
`tracks_on_keep = 1633` (real vessels tracked — MUST NOT fall under any
suppressor), `false_on_suppress = 3070` (track-scans in the two SUPPRESS regions
— a valid suppressor should shrink this), `false_unlabeled = 18295` (the rest of
the philos over-count, outside every labelled region). This is the un-gameable
surface: a config that "wins" by deleting the ferry shows `tracks_on_keep` drop.

**R8.3 gate 1 — KEEP canaries (pass TODAY under land):** all four KEEP regions
covered by a confirmed track within radius — closest tracks 0.17 m (ferry_v1_a),
0.47 m (ferry_v1_b), 1.2 m (loiterer_v2), 3.6 m (ranks_84_95). The tracks sit on
the exact radar returns the labels were located from.

**R8.3 gate 2 — stop→go (pass TODAY under land):** a single confirmed track
(id 13) holds a **stable id** across the ferry's t≈90 transition (present in
both the ferry_v1_a window and the ferry_v1_b window) and **reports motion**
(late SOG 2.89 m/s in t≈110–116). 4 ids span both regions; the other 3 are SOG≈0
(static structure inside the region radius). This is the real-data instance of
the ADR 0002 rule-3 recovery gate — the synthetic `harbor_anchored_gets_underway`
gate stays alongside.

**Takeaway:** current coastal PMBM already tracks the real vessels in this
zero-AIS clip and holds the ferry's identity through its stop→go — the gates
document that safety. The decomposition + canaries are now the measurement the
corroboration layer (increment 6) must improve (`false_on_suppress` ↓ while
`tracks_on_keep` flat).

## 2026-07-03 — Stage 1b-ii detector bench gates: death-spiral guard, presence-over-classification, static→moving recovery (increments 4/5/7) [Cl-3]

Three end-to-end bench gates for `imm_cv_ct_pmbm_occupancy_detector` on complete
synthetic truth (`tests/benchmark/test_occupancy_detector_gates.cpp`), plus the
formal M2 gate split (§5.6 of `synthetic-clutter-bench.md`). 8 seeds, A/B vs
`imm_cv_ct_pmbm_land`.

**Increment 4 — death-spiral guard (`dense_clutter_datum`).** New scenario =
`dense_clutter` with a datum attached so the live layer actually wires (the
plain `dense_clutter` A/B "safety" was vacuous — no datum ⇒ layer OFF ⇒
byte-identical for a trivial reason). Wired on dense uniform clutter: land
lifetime 0.845 → detector 0.836 (−0.009), gospa 13.07 → 13.09. **No death
spiral** (the λ_C spike regressed this same metric 0.90 → 0.26). The detector
does classify ~4 structures / 65 suppress-hits here because synthetic
`dense_clutter` concentrates its false alarms in a ~12-cell box (pathologically
high per-cell revisit vs a realistic spread field), so a few cells cross the
adaptive bar — but it suppresses *phantom clutter births*, not the real AIS
targets, so lifetime/gospa hold. On realistically spread / real clutter the
adaptive bar rejects it outright (R4: philos clutter 0.28 ≯ its own background).

**Increment 5 — presence over classification (`harbor_complete_truth`).** Movers
(ids 1–2) hold lifetime 1.0 / 0.997 and are not hazards. Anchored boats (ids
3–5) stay **tracked** (life 0.94–0.97, `occ_truth_in_hazard` ≈ 0, KEEP-as-hazard
fraction 0.04) — at P_D 0.9 they confirm in scans 1–2, before the layer
classifies them, and birth-channel suppression cannot remove an already-confirmed
cohort. So the feared 0.975 → 0.9725 boat→hazard trade is **negligible at this
yardstick**; the presence check (track OR hazard, never neither) passes via the
track path. The new `occ_truth_in_hazard:truth_<id>` bench column (truth's final
position ∈ an emitted hazard's keep-clear ring — pure geometry, GOSPA-independent)
is what makes the three-way split machine-checkable.

**Increment 7 — static→moving recovery (`harbor_anchored_gets_underway`).** New
scenario: a non-cooperative boat anchored 10 scans then underway. truth_6
lifetime land 0.981 → detector 0.972 (structures 4.4, suppress_hits 24 → the
layer IS active), final_in_hazard 0 → **the mover is tracked while suppression
runs** (rule-3 safety). Honest limitation: at P_D 0.9–0.95 the boat confirms
before it can be suppressed, so the bench recovery gate proves "suppression does
not brick the mover" rather than exercising a genuine suppress→re-birth
transition — the precise bounded-latency decay is unit-tested at the model level
(`VacatedCellsRecoverWithinBoundedLatency`) and the real transition lives in the
churn / R8.3 stop→go / HAXR regimes.

**Takeaway:** the detector is safe end-to-end on complete truth (no death spiral,
presence conserved, movers preserved, recovery holds). The gates are valid
regression guards; the P_D-0.9 yardstick cannot exercise post-confirmation
suppression (the established confirmed-cohort wall), so the sharp invariants stay
with the model unit tests + churn/HAXR. M2 gate formally split three ways
(presence hard-gate / movers lifetime / classification-quality reported).

## 2026-07-03 — R4: philos cluster classification bounds the Stage 1b removable ceiling; persistence does NOT separate craft from structure [Cl-3]

Closed the R4 open sub-task (2026-07-02): per-cluster classification of the
philos persistent over-count against the Boston S-57 ENC
(`charts/philos_cluster_classification.py`, CSV + PNG). Classifies every
persistent 25 m radar cell; SUPPRESS requires BOTH `fixed_surface` AND the
curated `radar_clutter` layer to place charted structure ≤ 50 m (neither layer
alone decides). Per-CELL, not connected-component — 8-conn over a dense harbour
front over-merges shore + piers + offshore craft into one 1325 m blob whose
shore-touching centroid mislabels the whole mass (a methodology trap; the 25 m
cell is the honest unit). Dual chart-layer distances agree, resolving the
2026-07-02 layer discrepancy: the dominant 42.3585 N cluster is 350–650 m from
charted structure in BOTH layers (the earlier "1 m SLCONS" was the merge
artifact).

**Removable ceiling (return-mass split, n=1727 persistent cells, mass=11557):**

| class | cells | mass % | meaning |
|---|---|---|---|
| SUPPRESS_CHARTED | 914 | **49.5%** | chart-confirmed fixed structure/shore/aid → suppressible |
| KEEP_INCOV_UNCHARTED | 449 | **32.5%** | in charted water, 100 m+ from any charted structure → real craft (a charted harbor would show fixed structure); the 42.3585 N anchorage the largest single driver |
| UNKNOWN_INCOV / _OUTCOV | 273 | 14.2% | chart silent → needs a visual pass; defaults to KEEP |
| KEEP_ANCHORAGE | 85 | 2.7% | compact, inside a charted anchorage → moored craft |
| TRANSIENT_NEARLANE | 6 | 1.1% | hugs own-ship track, low dwell → wake/near-field |

**So a perfect structure detector can legitimately remove ~50% of the philos
over-count mass, not all of it — ~35% is real craft it MUST preserve (ADR
0002).** The reference λ_C spike deleted ~58% of philos `gospa_false`
(2440→1020) — which OVERSHOOTS the 49.5% structure ceiling into KEEP mass,
quantitatively confirming its `card_err` 3.95→−3.25 over-deletion. This is the
anti-gaming bound the discussion asked for: any philos suppression that removes
> ~50% of the persistent mass is deleting real craft, regardless of what the
AIS-only truth scores. **(Updated 2026-07-03, R8.6 — see the entry at the top:**
the largest KEEP driver (ranks 1–2, 42.3585 N anchorage) is now frame-confirmed
KEEP_MIXED and the largest in-coverage ex-UNKNOWN group on `close_approach`
resolves toward KEEP — **corroborating** the ≤49.5% deletable bound with direct
video evidence (the number is unchanged) and closing, for this clip's largest
UNKNOWN group, the hope that the UNKNOWN slice hides more suppressible structure.**)

**Detector-design finding (the load-bearing one):** dwell/persistence does NOT
separate structure (p50 0.68) from craft (p50 0.64), and their footprints
overlap (extent p90 127 m vs 108 m; cells/comp p90 7 vs 6). **No occupancy-grid
tuning — cell size, bar, extent floor — can split the 35% KEEP craft from the
50% SUPPRESS structure, because anchored boats are as persistent and as compact
as fixed structure on real data.** The Stage 1b-ii detector MUST discriminate by
chart / AIS / camera corroboration, not persistence + extent. This is the
real-data evidence behind "the wall is the detector, not the channel."

Canaries emitted for the later channel decision: SUPPRESS canaries
(chart-confirmed PONTON/SLCONS/PILPNT clusters, e.g. 42.3758 N/−71.0495 E) that
a valid suppressor SHOULD hit; KEEP canaries (42.3585 N/−71.0877 E anchorage and
the offshore group) that it must NOT — with maps URLs for the UNKNOWN visual
pass. No philos gospa is cited as a suppression win anywhere.

## 2026-07-03 (follow-up) — Stage 1b-i occupancy: philos WAS reachable (cwd artifact); birth-only works on *tuned synthetic churn* but is inert on real data at every tuning [Cl-3]

This follow-up **corrects two claims** in the entry below it (kept for the record):
(1) philos was NOT absent, and (2) birth-only suppression is NOT inert everywhere.

**Correction 1 — philos is reachable.** The philos replay/A-B tests resolve the
fixture via *cwd-relative* paths (`tests/fixtures/philos/out/...`) and
`GTEST_SKIP()` only when those don't resolve. `ctest` runs test binaries from
`build/`, so they skip there. Run `./build/navtracker_tests` **from the repo
root** and every philos test runs. The fixture (7 clips) is present and
gitignored, not missing. "philos unavailable in this environment" was a cwd
artifact.

**Reference spike reconfirmed on philos (from repo root), λ_C-coupled
`feed_clutter_map`, `imm_cv_ct_pmbm_land` A/B, 5 seeds:**

| scenario | metric | base | +cluttermap | Δ |
|---|---|---|---|---|
| philos | gospa_mean | 63.13 | 51.83 | **−11.3** |
| philos | gospa_false | 2440 | 1020 | **−1420** |
| philos | card_err | **3.95** | **−3.25** | −7.2 (overshoots *negative* — deletes more than AIS truth cardinality) |
| dense_clutter | lifetime | 0.90 | **0.26** | **−0.64 (death spiral)** |

The spike's philos win is real but **unsafe** (dense_clutter collapses) and
**over-deletes** (card_err flips negative) — exactly why 1b-i excluded the
existence channel. This is the anti-gaming red flag: the win partly rewards
deleting non-AIS objects the AIS-only truth cannot score.

**Correction 2 — birth-only is not inert; it has one operating regime.** New
instrument `OccupancyAB.BirthOnlySuppressionAcrossRegimes`: A/B of
`imm_cv_ct_pmbm_land` vs the occupancy config at three classifier tunings
(default 25 m/α0.3/bar0.5/ext4; *sensitive* 50 m/α0.15/bar0.25/ext3; *coarse*
100 m/α0.3/bar0.2/ext3), across a regime axis. New churn scenario
`harbor_complete_truth_churn` = `harbor_complete_truth` with the uncharted pier
at per-scan P_D 0.4 (vs 0.9) — so phantoms decay and must re-birth; complete
truth (boats scored) → card_err/lifetime honest. 8 seeds:

| scenario | classifier | structures | suppress_hits | gospa_false Δ vs land | lifetime |
|---|---|---|---|---|---|
| harbor_complete_truth (P_D 0.9) | default | 0.875 | 0.25 | −1.3 | 0.975 |
| harbor_complete_truth (P_D 0.9) | sensitive | 1 | 3.75 | **−29** | 0.975 |
| **harbor_complete_truth_churn (P_D 0.4)** | default | **0** | 0 | 0 | 0.975 |
| **harbor_complete_truth_churn (P_D 0.4)** | **sensitive** | **1** | **25.9** | **−78 (−4.6%)** | **0.975** |
| harbor_complete_truth_churn (P_D 0.4) | coarse | 0.625 | 2.5 | (small) | 0.975 |
| **philos (real)** | default | **0** | 0 | 0 | 0.369 |
| **philos (real)** | sensitive | **0** | 0 | 0 | 0.369 |
| **philos (real)** | **coarse** | **3** | **0** | **0** | 0.369 |
| dense_clutter | all three | 0 | 0 | 0 | 0.845 |

**Synthesis — a regime squeeze and a two-layer wall.**
- On **synthetic churn with a tuned classifier**, birth-only suppression **works
  and is safe**: it fires 26×, cuts false mass 4.6%, holds boat lifetime, leaves
  dense_clutter byte-identical. The earlier "inert everywhere" was an artifact of
  (a) the P_D-0.9 yardstick, where the cohort confirms in scans 1–2 and the
  within-scan-order block dominates, and (b) a persistence bar (0.5) set *above*
  the churn per-cell P_D (0.4), so the default classifier saw nothing to gate.
- On **real philos, birth-only delivers nothing at any of the three tunings**,
  for two *independent* reasons a channel change cannot fix:
  1. **Classifier vs sparsity/smear** — at 25–50 m the per-cell EWMA persistence
     (mean ≈ per-cell P_D) never nears any usable bar (peak 0.17–0.30); real
     fixed returns are sparse per scan and smeared across cells by own-ship
     projection error. Coarsening to 100 m finally classifies (structures=3).
  2. **Channel reach** — but even then `suppress_hits=0`: the philos phantoms are
     *already-confirmed, association-maintained tracks*, which the birth channel
     cannot touch (the within-scan-order/confirmed-cohort wall, now proven on
     real data even when classification succeeds).
- So the real-data wall is two-layered: a classifier that fires on sparse/smeared
  returns (needs coarse cells and/or chart/AIS/camera corroboration) **and** a
  channel that can reach confirmed phantoms (an existence channel). An existence
  channel addresses layer 2 only — and only once layer 1 exists — and damping the
  existence of confirmed tracks near classified structure is precisely the
  ADR-0002 vessel-safety risk (at 100 m a real moored/transiting vessel merges
  into a structure component). No philos *quality* claim is made here (philos
  Δ = 0), so the AIS-only-truth gaming risk does not arise; the only quality
  claim is on complete-truth synthetic churn.

**Status: layer shipped opt-in; birth-only suppression proven (safe, small) on
tuned synthetic churn, inert on real data. Not promoted.** 1b-ii priority is the
**structure detector** (coarse-grid / projection-robust + corroboration), not the
suppression channel — birth-only is an adequate channel once the detector fires
on real returns. Instrument commits below.

## 2026-07-03 — Stage 1b-i live occupancy layer: built, safe, but birth-only suppression is INERT on all synthetic fixtures [Cl-3]

**[Partly corrected by the follow-up above: philos was reachable (cwd artifact),
and birth-only is not inert on a tuned classifier in the churn regime. The
classification observations and the within-scan-order root cause below stand.]**


Built `LiveOccupancyModel` (design 2026-07-01): a datum-stable occupancy grid
that accumulates the PMBM per-scan (position, 1−r) feed as per-cell EWMA
persistence and, via connected-component extent, classifies persistent-AND-
extended structure. Wired as both the birth-suppression model
(`setStaticObstacleModel`) and a new occupancy feed (`setLiveOccupancyFeed`,
independent of the detection model → no λ_C coupling). New opt-in config
`imm_cv_ct_pmbm_occupancy` = `imm_cv_ct_pmbm_land` + the layer.

**Classification works.** Instrumented run (3 seeds, all sim scenarios, debug
counters `peak_structures` / `peak_persist` / `suppress_hits`):

| scenario | peak_structures | note |
|---|---|---|
| harbor_complete_truth / _charted_pier / _compact_dolphin | 1 | pier → structure ✓ |
| harbor_boat_near_pier | 1 | pier classified; boat stays compact ✓ |
| harbor_large_anchored_ship | **2** | **R3 dangerous case reproduced — the ship hull is classified as structure** |
| shore_clutter_open / _nearshore | **0** | scattered clutter persistent (0.96) but NOT extended → extent gate correctly rejects ✓ |
| dense_clutter | 0 | transient uniform clutter never persists ✓ |

**But birth suppression never bites.** `suppress_hits ≈ 0` on every fixture; A/B
`_occupancy` vs `_land` (3 seeds, all sims) is byte-identical on the key gates
(harbor_complete_truth, dense_clutter, clean geometry) and moves nothing
material elsewhere (harbor_boat_near_pier gospa_false 2326.7→2325.0, −0.07%;
harbor_large_anchored_ship 3785→3783). **Root cause (instrumented, not guessed):**
within a scan the order is *births → feed*, so a pier's phantom cohort is born in
scans 1–2 **before** the layer can classify anything; those Bernoullis then
confirm via *association* (which birth suppression cannot touch), and
`smart_birth_skip_existing` owns the region thereafter, so no later birth ever
queries the classified structure (`suppress_hits=0`). Birth-channel-only
suppression is structurally unable to remove an already-confirmed cohort.

**Interpretation.** The layer is correct and SAFE (off = bit-identical; boats /
movers / uniform clutter never suppressed — the extent gate holds; no
dense_clutter regression) but INERT on the available fixtures. The design's
demonstrated over-count reduction (philos gospa 63→52) came from the λ_C-coupled
`feed_clutter_map` spike — an *existence*-channel effect — which the design
deliberately excluded from 1b-i for safety (an existence penalty near structure
would also damp a real vessel transiting past a pier; that needs the 1b-ii shape/
motion discriminator to be safe). The one available structured fixture (harbor)
confirms birth-only is too weak; **philos, the design's primary suppression gate,
is unavailable in this environment** (replay fixture absent — the replay tests
skip). So the regime where birth-only *might* still bite (dense, churning,
persistently-unclaimed returns) cannot be measured here.

**Status: layer shipped opt-in; suppression unproven. Not promoted.** Decision on
direction (existence-channel extension behind a flag vs. defer suppression to
1b-ii / philos) pending. Foundation committed: 72e4a9f, 20f1614, f922011.

## 2026-07-02 — PDA soft detected-branch update (open-sea K=1 gap) [Cl-3]

Closes the north-star's "open (next)": under K=1 GNN a detected PMBM Bernoulli
hard-commits to its single lowest-cost gated measurement, so a gate-CLOSER
clutter return drags a real open-sea track off-target (dense_clutter lifetime
0.823 vs MHT 0.925). New opt-in `use_pda_soft_detected_branch` (default off):
the detected branch β-weights the winner's per-cell update with any gated
measurement NOT claimed by another existing Bernoulli (pool), moment-matched with
the innovation-spread term — only the STATE changes, the hypothesis weight still
uses the winner, so K=1 / Murty / births are untouched. Reduces to today's hard
update when the pool is size 1.

**A/B `imm_cv_ct_pmbm_land` vs `imm_cv_ct_pmbm_land_pda` (10 seeds, sim):**

| Scenario | lifetime | gospa | card_err | gospa_false |
|---|---|---|---|---|
| dense_clutter (open-sea) | **0.823→0.847** | 13.6→13.1 | −0.19→−0.14 | 38→35.5 |
| parallel_lanes_dense | 0.976→0.982 | 14.7→14.6 | — | 4→4.5 |
| harbor_large_anchored_ship | — | 63.7→**56.2** | 19.0→**14.6** | 3827→**2953** |
| harbor_charted_pier / complete | — | 51.4→46.9 | 12.0→9.8 | 2435→1999 |
| harbor_boat_near_pier | — | 53.0→50.1 | 11.7→9.9 | 2433→2103 |

Open-sea lifetime up (toward MHT); **extended-target / anchored over-count DROPS
hard** (the multi-return hull pooling collapses spurious tracks — card_err −2 to
−4, gospa_false −330 to −874) → no anchored regression, the opposite. Single-
return scenarios unchanged (reduce-to-hard). Flag off = byte-identical (full
suite green).

**Philos REPLAY over-count gate PASSED:** `philos` gospa 63.13→63.08,
`philos_radartruth` 67.08→67.04 (both a hair better; card_err / lifetime /
gospa_false unchanged). Exactly as the unclaimed-only pool predicted — in dense
philos, competing returns are claimed by other established tracks → excluded from
the pool → pool ≈ 1 → hard-like → no over-count. Net: PDA soft update is a clean
win (open-sea up, extended-target over-count down, philos/anchored flat) with
zero regression. `imm_cv_ct_pmbm_land_pda` shipped opt-in; a promotion-to-default
call wants the autoferry replay A/B + real-data error bars next.

## 2026-07-02 — Static-review code-review, round 2 (9 findings)

A second review of the round-1 fixes. The three load-bearing claims held (land
factor genuinely preserved, merge-guard byte-identical for default-off, A/B
story stands), but two fixes had introduced second-order problems:

- **Merge guard REVERTED (finding #1).** The round-1 distinct-same-scan-claim
  merge guard assumed one detection per target per scan — FALSE for a fused
  multi-sensor batch: one target seen by AIS+radar (or a large target split into
  two plots) yields two distinct-claim Bernoullis that MUST merge; the guard
  would leave a duplicate track per vessel, and its own test only passed because
  it never left the never-merge regime. Reverted. The single-index clutter-feed
  leak it targeted (survivor's claim credited on a merge, folded return fed as
  clutter) is accepted as a documented limitation until the feed carries a claim
  SET. `feed_clutter_map` is default-off, so no default-config impact either way.
- **take_b_claim corrected (finding #3):** it could drop a's real claim for b's
  −1 when r_b > r_a; now guarded (`b.idx>=0 && (a.idx<0 || r_b>r_a)`).
- **Negative keep_clear (finding #2):** kept the clamp-to-0 (hazard preserved,
  review 1) but made it explicit — a negative/zero keep_clear = footprint-only
  hazard with NO alarm ring; restored the dropped test coverage + documented the
  contract. A per-field diagnostic channel is the deeper fix (out of scope for a
  pure parser).
- **Consolidation (findings #6/#7/#8):** `birthScale`, the obstacle/land prior
  queries and the R1 gate-reference block were re-evaluating the models 2–3× per
  candidate and copy-pasted across both builders. Unified into `birthPriorsAt`
  (one model eval) + `applyBirthPriors` (one shared block). **A/B (all 11 pmbm
  configs × 22 scenarios): 0 focus-cell change — byte-identical.**
- **Docs/chart (findings #4/#5/#9):** fixed the stale `NewTargetCandidate` gate-
  reference comment; regenerated the stale philos coverage PNG (derived legend);
  parse `fixed_surface.geojson` once. 889 tests green.

## 2026-07-02 — Backlog #15: processBatch orders the batch (ergonomics quick fix)

Both `MhtTracker` and `PmbmTracker` `processBatch` now `stable_sort` the scan by
time (behind an `is_sorted` fast-path), so the canonical fixed-rate consumer
(dump everything since the last tick) need not pre-sort. **Observation: no bench
delta** — real/scenario feeds are already time-sorted, so the sort is a no-op and
the whole suite (889 tests) + the pmbm A/B stay bit-identical. The behavioural
proof is `tests/pipeline/test_batch_ordering.cpp`: MHT was genuinely wrong on an
unsorted batch (it used `scan.front().time` as the scan instant → different
`last_update` and drifted state; RED before the fix, green after), while PMBM was
already order-robust (predicts to `t_max`, set-wise association — the equivalence
test passes pre-fix; its sort is defensive + pins the optional idle-decay knob's
`front()` read). Side quest, not tagged to a claim. See backlog §15.

## 2026-07-02 — Static-review code-review findings (R1/R2/R7 seams)

A high-effort code review of branch `static-branch-review-fixes` raised 10
findings; verified each against the code before acting. Four were real
correctness/safety bugs (fixed, TDD); the rest were latent/trade-off (documented
the true contract). **A/B (imm_cv_ct_pmbm × all 11 pmbm variants × 22 sim
scenarios, 5 seeds): 0 focus-cell changes vs pre-fix** — every PMBM fix is inert
on default configs. Numbers only move on the `feed_clutter_map` path (default
off) and where a static-obstacle model is wired with a land model (no sim/philos
config does both).

- **#3 (real):** the R1 phantom-birth-floor relaxation gated on the *fully*
  unsuppressed intensity, stripping BOTH land and obstacle suppression in their
  overlap → disabled ADR-0001's near-shore no-birth zone wherever a keep-clear
  ring crosses the shore band. Fixed to relax the **obstacle factor only**, keep
  `(1 − c_land)` (new `landSuppressionAt` helper). RED test
  `ObstacleOverlapDoesNotStripLandZone` (birthed at 0.0055, should be 0) → green.
- **#2 (real, feed-only):** `mergeBernoulliDuplicates` dropped one claim when two
  state-close Bernoullis each claimed a *different* measurement in the same scan,
  leaking that real return to the clutter map as full-weight clutter. RED test
  `MergedSameScanReturnsStayCredited` reproduced the leak. Fix: refuse to merge
  two distinct-claim Bernoullis — **but the first cut applied this merge-wide and
  regressed every config** (measured +card_err / +gospa_false / +ospa, 306 focus
  cells). Root cause: the leak only exists on the `feed_clutter_map` path, so the
  merge change was scoped to `cfg_.feed_clutter_map`; re-A/B → 0 cells changed.
- **#1 (overclaim, not a bug):** an admitted birth still materialises at its
  suppressed `r_new`; deep land×obstacle composition can drive that below `r_min`
  → pruned same scan, not trackable position-only. Documented the boundary +
  characterization test `DeepCompositionNotTrackablePositionOnly`; did NOT floor
  existence to `r_min` (would seed clutter phantoms — the over-count the shore
  work fights). Sensor-aware ADR-0001-A3 is the real cure.
- **#6 (safety):** a negative radius dropped the whole charted obstacle; changed
  to clamp the field to 0 and keep the hazard (losing a charted hazard over one
  bad optional field is the worse failure).
- **#4/#5/#7/#8/#9/#10 (docs/contracts):** de-hardcoded the chart script's bridge
  count + ENC-dict lockstep note (#4); documented the GeoJSON empty-on-corruption
  caller contract (#5); `soft_max` cap is default-gate-only, a lower gate is a
  wiring responsibility (#7); the hazard evaluator relies on stable obstacle
  indexing (#8); `source_id` must be a stable feature id for `hazard_id`
  stability (#9); updated the required algorithm doc `static-obstacle-birth-prior.md`
  with the R1 floor interaction (#10).

## 2026-07-02 — R3 (static review): extent-is-interim gate scenarios + 1b-i baseline

Static-branch review ticket R3. Added Dalhaug 2025 (arXiv:2502.18368) to
`docs/references/` and marked extent as an **interim** discriminator in the Stage
1b design + ADR 0002 (the literature discriminates by classification, not
geometry). Added the two failure-direction gate scenarios and recorded their
1b-i "before" numbers (imm_cv_ct_pmbm, 5 seeds) — NOT pass/fail gates under 1b-i:

| Scenario | card_err | gospa_false | lifetime | 1b-ii target |
|---|---:|---:|---:|---|
| `harbor_large_anchored_ship` (real, extended) | 19.06 | 3846 | 0.978 | **KEEP** the ship |
| `harbor_compact_dolphin` (fixed, compact) | 12.64 | 2561 | 0.974 | **SUPPRESS** the phantom |

- `harbor_large_anchored_ship`: the real ship (truth id 6) is tracked at lifetime
  0.978 under 1b-i, but its ~150 m hull spawns extra tracks (card_err 19 vs the
  5-target harbor baseline 11.6). An **extent-only** 1b-ii discriminator would
  wrongly SUPPRESS the extended hull → the ship LOST. That is the KEEP failure
  direction 1b-ii's corroboration (chart/AIS/camera) must fix.
- `harbor_compact_dolphin`: the compact fixed dolphin (no truth) adds ~1 phantom
  track (card_err 12.6 vs 11.6). An extent discriminator KEEPS it (compact →
  vessel-like) → the SUPPRESS failure direction.

Both are deterministic + contract-tested (`test_harbor_gate_scenarios.cpp`). They
are the "before" reference for the Stage-1b-ii classification work; not gated on
under 1b-i.

## 2026-07-02 — R4 (static review): philos chart-coverage field-check committed

Static-branch review ticket R4. The strongest quantitative evidence for the
philos over-count attribution lived only in the uncommitted working tree
(`charts/philos_chart_coverage.py` + PNG). Committed it (fixed a stale hardcoded
scratchpad `OUT` → `ROOT/charts`, env-overridable) and re-ran against the current
Boston ENC (US5BOSCC/CD) + chart GeoJSON. Field-check numbers (top-100 strongest
persistent-structure clusters — the actual over-count drivers):

- **0 %** within 75 m of a charted **bridge** (6 % within 150 m).
- **32 %** fall **outside ENC chart coverage** (M_COVR) entirely.
- **37 %** are near a bridge (≤150 m) OR outside coverage; ~63 % remain
  unexplained by any chart layer.
- Two dominant groups: an in-coverage cluster at **~42.3585 N / −71.0875 E**
  (~350–470 m from any charted feature, ~500–600 m from bridges) and an
  **outside-ENC** group at **~42.376–42.379 N / −71.046 E**.

This is the quantitative backing for the R4 doc reconciliation (design spec
§14.10 + ADR 0002 now say "persistent uncharted structure dominates; a minority
are moored craft — mixture"). It also confirms the largest slice of the residual
over-count is **not chartable** — the honest lever is live static-occupancy
(Stage 1b/2), not the chart (cf. 2026-07-01 "charts are a ~⅓ partial lever").

**Open sub-task (needs imagery, not doable in this environment):** the top-20
clusters' geometric table (lat/lon, return count, distance-to-chart,
distance-to-bridge, in/out ENC coverage) is emitted by the script, but the
per-cluster *visual* classification (fixed structure vs moored craft vs
own-ship-wake vs sea clutter) requires satellite / raw-radar overlay inspection.
Deferred — it decides how much of the residual Stage 1b can actually crush.

## 2026-07-02 — R6 (static review): boat-near-pier gate; R1 not load-bearing on default configs (measured)

Static-branch review ticket R6. Added `harbor_boat_near_pier`: the R5 charted-pier
scenario plus one anchored zero-velocity truth boat (id 6) 20 m off the pier line
— inside the 50 m keep-clear buffer, outside the 10 m footprint — the
boat-next-to-structure case the whole effort is about. Contract-tested (6 closed
truth targets, time-sorted into 40 complete {1..6} groups) and added to the M2
gate.

**Gate (imm_cv_ct_pmbm vs imm_cv_ct_pmbm_static, 5 seeds):** aggregate
lifetime_ratio (static) = **0.975** — the near-pier boat is tracked (a dropped
boat would pull the 6-target aggregate to ~0.81) — while card_err falls 11.6 →
7.5 (pier suppressed). The charted keep-clear buffer is **soft**, not a no-birth
zone: a moored boat next to structure still initiates and holds.

**Finding — R1 is NOT load-bearing on any default config here.** A git-version
A/B (R1 in vs out) on this scenario is **byte-identical** — the boat is tracked
either way. Under `imm_cv_ct_pmbm_static` (floor 0.05 < birth target) the buffer
suppression does not drive the birth below the floor, so R1's obstacle-scoped
relaxation never fires; and the only regime where it would (floor == target, i.e.
`coverage_land`) wires no obstacle model. So R1, like R2, is a latent-bug fix +
Stage-1b prerequisite with **no delta on any current default config** — consistent
with the byte-identical philos A/B. R1's clean discrimination lives in the unit
tests (`test_pmbm_birth_floor.cpp`), where a floor==target config with an obstacle
provably needs it. The scenario comment and gate test were corrected to reflect
this (no "R1 proven e2e" overclaim).

## 2026-07-02 — R5 (static review): Stage 1a charted-obstacle A/B measured (was "no measurement")

Static-branch review ticket R5. Stage 1a (the charted `StaticObstacle` birth
prior) shipped 2026-07-01 with **zero measured benefit** — no fixture had charted
hazards. Added `harbor_charted_pier`: identical measurements + truth to
`harbor_complete_truth`, but the pier is now charted as a line of `StaticObstacle`s
(footprint 10 m, keep-clear 50 m) via the scenario `syntheticObstacles()` hook.

**Measured A/B** (`imm_cv_ct_pmbm` vs `imm_cv_ct_pmbm_static`, 5 seeds; test
`SyntheticClutterAB.ChartedPierSuppressesPierKeepsBoats`):

| Metric | imm_cv_ct_pmbm | imm_cv_ct_pmbm_static |
|---|---:|---:|
| card_err_mean | 11.64 | **7.43** |
| gospa_false | 2362 | **1518** |
| lifetime_ratio | 0.974 | **0.975** |

Charting the pier removes ~4 phantom tracks (card_err 11.64 → 7.43, gospa_false
−36%) while every real target keeps its lifetime (0.975 == the harbor baseline).
The suppression is **partial by construction**: the hard footprint kills returns
*on* the pier, but the scenario's uniform sea clutter (5/scan, uncharted) is the
residual over-count — no chart layer addresses it (that is Stage 1b/2's job, cf.
the 2026-07-01 "charts are a ~⅓ partial lever" finding). This is the first
*measured* confirmation that the charted birth prior works. Real-data philos A/B
with the Boston ENC GeoJSON is a predictable partial repeat (deprioritised per
2026-07-01). north-star Stage 1a row updated from "no measurement" to these deltas.

## 2026-07-02 — R1 (static review): pre-suppression birth floor, SCOPED to obstacle composition (measured)

Static-branch review ticket R1
(`docs/superpowers/plans/2026-07-02-static-branch-review-fixes.md`). The bug: a
soft static-obstacle keep-clear buffer, composed with the land prior, multiplies
into a birth intensity whose `r_new` falls below `min_new_bernoulli_existence` —
so the phantom-birth floor silently turns the soft buffer into a **hard no-birth
zone** in the overlap, exactly where ADR 0002 promises a real vessel still
births. Fix = ADR 0001's parked "A2": check the floor against the
**pre-suppression** existence, materialise the Bernoulli with the tiny suppressed
`r_new` (above `r_min = 1e-3`, so it survives pruning and accumulates on
re-detection).

**The catch (measured, philos guard).** A2 applied UNCONDITIONALLY also relaxes
the LAND-only near-shore no-birth zone — which ADR 0001 kept *on purpose* to
protect the philos win (it had rejected the sibling "A1" gate-lowering for the
same regression). A clean git-version A/B on the real philos replay:

| philos config | A2 off (before) | A2 unconditional | A2 scoped to obstacle (shipped) |
|---|---|---|---|
| `imm_cv_ct_pmbm_land` (recommended) | card 3.95 / gospa 63.1 | 3.95 / 63.1 | **3.95 / 63.1** |
| `imm_cv_ct_pmbm_coverage_land` | card 6.9 / gospa 73.1 | **40.15 / 106.9** ✗ | **6.9 / 73.1** |

Unconditional A2 regressed `coverage_land` (floor == birth_existence_target ==
0.1, so *any* land suppression drops below the floor) — card_err +6.9 → **+40.15**,
gospa 73 → **107**, gospa_false 3550 → 10220: it re-admitted the near-shore water
clutter ADR 0001 was suppressing. `imm_cv_ct_pmbm_land` (floor 0.05 < target) was
immune either way.

**Decision (2026-07-02).** Scope the pre-suppression relaxation to births where a
**static obstacle** contributes (`obstacleSuppressionAt(mean) > 0`). Land-only
suppression keeps its ADR 0001 gating role. Result: the composition hard-drop is
fixed (unit tests: a stationary target inside a keep-clear buffer + soft shore
band now births AND confirms), ADR 0001's land-only zone is preserved
(`LandOnlySuppressionPreservesAdr0001NoBirthZone`), and both philos configs are
**byte-identical** to A2-off. philos wires no obstacle model, so it is untouched;
the fix bites only near charted obstacles (harbor / R5 / R6 scenarios). Guarded by
5 unit tests in `tests/pmbm/test_pmbm_birth_floor.cpp`; full suite 875 green.
ADR 0001 amended (A2 adopted, obstacle-scoped). The pure land-only
anchored-vessel case remains open (ADR 0001 A3, sensor-aware — needs EO/IR/AIS).

## 2026-07-02 — R2 (static review): clutter-feed labeling fixed; dense_clutter regression is NOT the labeling (measured)

Static-branch review ticket R2
(`docs/superpowers/plans/2026-07-02-static-branch-review-fixes.md`). Two competing
claims were on the table for the Stage 1b clutter-feed dense_clutter regression:

- **R2 ticket + north-star Stage 1b row:** the feed's nearest-neighbour-at-timestamp
  reconstruction is the *root* of the regression (lifetime 0.90 → 0.26).
- **eval-log 2026-07-01 (Stage 1b spike):** the regression is the `1 − r`
  co-located death spiral on *uniform* clutter, needing a persistence /
  spatial-concentration gate (Stage 1b-ii).

**Measured A/B** (`imm_cv_ct_pmbm_land` vs `+use_clutter_map+feed_clutter_map`,
`dense_clutter`, 5 seeds; test
`PmbmClutterFeedR2.TrueAssignmentIsOrthogonalToDenseClutterSpiral`):

| Config | lifetime_ratio |
|---|---:|
| base (no feed) | **0.9025** |
| +feed, NN reconstruction (before R2) | 0.26 |
| +feed, true-assignment labeling (after R2) | **0.26** |

The labeling method is **orthogonal** — byte-identical 0.26 either way. This
**disproves** the R2-ticket / north-star attribution and **confirms** the
2026-07-01 diagnosis: the spiral is the `1 − r` weighting of a low-r target's OWN
(correctly-claimed) returns on uniform clutter, not a mislabel of which Bernoulli
claimed them. The real cure remains the Stage 1b-ii persistence + spatial gate
(uniform clutter never crosses that bar).

**What R2 shipped anyway (correctness, no bench delta).** PMBM's clutter feed now
credits each return to the Bernoulli that actually claimed it under the dominant
hypothesis's association (`Bernoulli::last_claimed_meas_index`, written in
`enumerateChildren`, reset on misdetection, carried through duplicate merge with
the survivor's `last_update`), replacing the nearest-neighbour-at-timestamp
reconstruction that (a) could double-claim in close-pair geometry, (b) ignored the
`(sensor, model)` bundle, and (c) fell back to the meaningless `sensor_position_enu`
for bearing-only returns. Because an unassigned return births-and-claims a new
Bernoulli anyway, and the NN-collapse pathology does not occur in the available
synthetic scenarios, the change is a **no-op on every current bench** (the philos
fixture is unavailable in this environment) — a latent-bug fix and a correctness
prerequisite for Stage 1b-ii, not a metric mover. Guarded by the determinism +
flag-semantics unit tests plus the characterization test above. `feed_clutter_map`
stays default-off. Decision recorded: keep the correct labeling fix, correct the
docs, defer the dense_clutter cure to Stage 1b-ii (option A, 2026-07-02).

## 2026-07-02 (corrected) — harbor_complete_truth Milestone-1 baseline under imm_cv_ct_pmbm

**Purpose.** Capture the "before" numbers on the `harbor_complete_truth` honest
yardstick (see `docs/algorithms/synthetic-clutter-bench.md §5`). This is the
baseline the live static-occupancy layer (Milestone 2) must beat. Run with 5 seeds;
config `imm_cv_ct_pmbm` (no coastline, no static-occupancy layer active).

**⚠️ Correction (2026-07-02).** The first version of this entry recorded
`card_err +13.32 / gospa 53.02 / gospa_false 2705.5 / gospa_missed 41.5 /
lifetime 0.92`. Those numbers were **invalid** — a truth-fragmentation bug (same
family as the 2026-06-10 autoferry finding): `addAnchoredBoats` appended the
anchored boats' truth as a second time-run onto the movers' truth without
re-sorting, so `BenchRunner::groupTruth` (which buckets only on a timestamp
change) split the run into **80 groups** (40 mover-only + 40 boat-only) instead
of 40. The mover-only groups scored every correctly-tracked anchored boat as a
false track; the boat-only groups replayed the already-exhausted measurement
stream, snapshotting the final tracker state 40 more times. Fix: `addAnchoredBoats`
(and the other additive builders) now sort truth as well as measurements, plus a
contract test asserts truth is time-sorted into exactly 40 complete {1..5} groups.
The corrected numbers below supersede the originals.

**Measured numbers (5-seed mean, test `HarborCompleteTruthBaseline.TodaysPmbmMetrics`):**

| Metric | Value |
|---|---:|
| card_err_mean | **+11.64** |
| gospa_mean | 50.63 |
| gospa_false | **2362** |
| gospa_missed | 34 |
| lifetime_ratio | **0.974** |

**Interpretation against expected verdicts:**

- `card_err_mean = +11.64` — today's PMBM over-counts by ~12 phantom tracks per
  scan on average. With 5 truth targets, this is a severe over-count. The pier
  (fixed returns, no truth) and uniform clutter (transient, no truth) are the
  sources; without a suppression layer every persistent pier return accumulates
  enough evidence to birth a Bernoulli.

- `gospa_false = 2362` — the vast majority of GOSPA penalty comes from false
  tracks. This confirms the pier/clutter phantom-track hypothesis: a single pier
  point confirmed over 40 scans contributes far more false-track GOSPA than a
  momentary clutter miss.

- `gospa_missed = 34` — small but non-zero misses. Some truth-matched scans (most
  likely from the anchored boats, whose zero-velocity makes them look like clutter)
  are not picked up by an active track on every seed.

- `lifetime_ratio = 0.974` — anchored boats (ids 3–5, zero velocity) AND movers
  (ids 1–2) are currently tracked for ~97 % of their lifetime. The tracker finds
  real targets very well even in this cluttered scene. The occupancy layer must
  maintain this (not drop boats while suppressing the pier).

**Takeaway.** Today's PMBM cannot distinguish pier returns from vessel targets —
card_err +11.64 and gospa_false 2362 confirm that. The high lifetime_ratio (0.974)
is the value to protect. The Milestone-2 A/B must show: gospa_false ↓, card_err_mean
↓, lifetime_ratio ≥ 0.974. This entry is the binding "before" reference.

---

## 2026-06-22 (Phase 8, multi-agent review fixes + iter 4 verification correction) — [Cl-3 PMBM Phase 8] 6 bug fixes + 5 tests + arch + perf: head_on -6.4 % GOSPA / -5.5 % T-GOSPA, +5 anchored T-GOSPA -4..-8 %, 0 unit-test regressions; iter 4 corrects overstated claims and strengthens R3

**Premise.** Phase 7 (Adaptive Birth) was followed by a 7-agent
parallel in-depth review (math vs MATLAB MTT-master, pruning, numerical
stability, test coverage, claim verification, architecture, performance).
The review surfaced 6 named bugs, 5 missing test categories, 1
architecture violation, and 3 perf hotspots. Phase 8 acts on them and
re-measures.

**Method — 3-iter polish.** All on `master` (1b44a9f → HEAD).

**Bug fixes shipped.**

- **R1 (PmbmTracker.cpp `mergeBernoulliDuplicates`):** merged
  existence was `1 − (1−r_a)(1−r_b)` (textbook independent fold),
  but the merge trigger only fires when (px, py, vx, vy) overlap
  closely → duplicates almost always trace to a common parent. The
  fold double-counted. Replaced with `max(r_a, r_b)` — keep the
  best-supported hypothesis without inflation.
- **R2 (PmbmTracker.cpp `rtsSmoothTrajectory`):** naive
  `predicted_covariance.inverse()` + no resymmetrise. Replaced with
  `Eigen::LDLT::solve` and `P = 0.5·(P+Pᵀ)` after each step.
- **R3 (estimators):** added `isMeasurementCovariancePsd(R)` guard
  at `EkfEstimator::update`, `UkfEstimator::update`,
  `ImmEstimator::update`. NaN/non-PSD R now early-returns; one bad
  NMEA frame can no longer poison `track.covariance` for the
  remainder of a replay.
- **R4 (UkfEstimator.cpp):** post-update `P -= K·S·Kᵀ` was the only
  estimator path without symmetrisation. Added LDLT-based gain
  solve + `0.5·(P+Pᵀ)`; future sigma-point Cholesky no longer
  drifts.
- **R5 (bench config):** `r_min` lowered 1e-3 → 1e-5 in
  `makePmbmConfig`, matching MATLAB `TPMBM_alive_filter.m`
  `existence_threshold = 1e-5`. Stops dropping legitimate low-r
  Bernoullis before posterior ramp.
- **R6 (PmbmTracker.cpp `bhattacharyya2D` → `bhattacharyyaState`):**
  position-only merge distance promoted to 4-D (px, py, vx, vy).
  Two near-coincident Bernoullis with opposite velocity no longer
  merge — was an id-merge bomb on crossings.

**Performance fixes shipped.**

- **P1 (`enumerateChildren`):** pre-gate before `estimator.update`.
  Cost cell stays +∞ when Mahalanobis fails the configured gate;
  cuts ~30–70 % of per-(Bernoulli, measurement) estimator updates
  depending on clutter density.
- **P2 (adaptive K = ceil(Nhyp_max · w_p)):** implemented as
  `Config::adaptive_k_best`. Per-parent K derived from weight
  share, capped at `k_best_per_hypothesis`. Mirrors MATLAB
  `PoissonMBMtarget_update.m:265`. Measured in iter 1 + iter 3:
  drives big philos/dense_clutter/sc4 wins (-15 % each) BUT
  exposes a structural interaction with the R1 merge max() formula
  on multi-vessel autoferry scenarios (+14..+27 % regression on
  sc13/sc16 anchored). Tighter merge threshold (1.0 → 0.25) in
  iter 3 did not recover. Shipped OFF in the bench config; parked
  until the K × merge interaction is understood.

**Architecture fix shipped.**

- `OwnShipProvider.{hpp,cpp}` moved physically from `adapters/own_ship/`
  to `core/own_ship/`. It's a pure domain type with no I/O — it
  belongs alongside `OwnShipVelocityEstimator` and `UereEstimator`.
  Closes the 3 `core/*` → `adapters/*` reverse-direction includes
  (CpaEvaluator, CpaOwnShip, MeasurementBuilders).
  `adapters/own_ship/OwnShipProvider.hpp` retained as a one-line
  shim for the ~37 callers; new code should include
  `core/own_ship/OwnShipProvider.hpp` directly.

**Tests added (5 new + 2 companion = 7 PMBM tests in `test_pmbm_phase8.cpp`).**

- T1 `BiasProviderShiftsPostUpdateBernoulliMean` +
  `NullBiasProviderLeavesMeasurementUntouched` — closes the zero-coverage
  gap on `PmbmTracker::setSensorBiasProvider`.
- T2 `BhattacharyyaMergeKeepsOlderIdAndDeletesYounger` +
  `BhattacharyyaMergeOffKeepsBothBernoullis` — pins id-stability
  invariant + the R1 fix (merged r ≈ post-miss-of-max, not the
  inflated independent fold).
- T3 `PmbmAdaptiveBenchIsByteIdenticalAcrossRuns` — extends
  `BenchDeterminism` to a PMBM config (was MHT-only; missed
  trajectory-snapshot ordering and adaptive-birth/K paths).
- T4 `PerSensorDetectionModelDifferentiatesBernoulliExistence` —
  two simultaneous measurements from sensors with very different
  (P_D, λ_C); high-confidence sensor's birth Bernoulli must outscore
  the noisy one. Closes the multi-sensor coverage gap.
- T5 `ConfirmedFiresOnlyOnUpEdgeNotOnReConfirmation` — exercises
  the Tentative → Confirmed re-promotion path. Discovered (and
  worked around in the test) that PMBM's empty-scan branch
  short-circuits before `firePmbmLifecycleEvents` / merge — noted
  as a follow-on.

**Iter 3 result (final, λ_birth=1e-5 + adaptive_k_best=false + all other Phase 8 fixes):**

Pinned `docs/baselines/pmbm_phase8_20260622.csv`. Net effect vs
Phase 7 baseline:

| Bucket | Phase 8 vs Phase 7 (adapt), iter 4 verified |
|---|---|
| head_on | GOSPA −6.4 %, T-GOSPA-raw −5.5 % (eval-log iter 1 originally said −9.1 / −11.2; rounded-int CSV reads were misleading vs full-precision deltas) |
| autoferry sc2/3/4/5/6 anchored | T-GOSPA-raw −4.2..−7.9 % (verified) |
| autoferry sc16/22 anchored | T-GOSPA-raw −0.3..−1.2 % small wins. sc17 anchored is 0.0 % — eval-log iter 1 erroneously listed it as a win |
| philos / dense_clutter GOSPA | unchanged (Phase 7 baseline retained) |
| autoferry sc13 unanchored | GOSPA +0.66 % (eval-log iter 1 incorrectly said +7.1 %; the rounded-int 14 → 15 was a rounding artifact) |
| **Unmentioned regressions surfaced in iter 4 verification**: | |
| autoferry sc5 id_switches | 5 → 10 (GOSPA unchanged) |
| autoferry sc3/sc2/sc16 id_switches | +1..+1.5 mean per scenario |
| crossing / head_on / philos id_switches | tiny increases (0.1..0.4 mean) |
| dense_clutter track_breaks | +11.5 % (1.30 → 1.45 mean) |
| autoferry sc22 track_breaks | +5.5 % |

734/734 unit tests pass (7 skipped, 0 failed; Phase 8 added 7 PMBM
tests + 5 missing-coverage scenarios).

**Takeaway.** R1–R6 + P1 are clean improvements; adaptive K (P2) is
the right MATLAB-faithful direction but interacts with R1 on
multi-vessel autoferry — parked behind `Config::adaptive_k_best`.
Anchored T-GOSPA-raw improved 4–8 % on top of Phase 7 across
sc2-6_anchored (verified); head_on closed −6.4 % GOSPA / −5.5 %
T-GOSPA-raw (verified, smaller than iter 1's rounded-int claim).
The big philos/dense_clutter wins were already in Phase 7; adaptive
K would push them further (~15 % each) at the cost of the documented
sc13/16 regression.

**Iter 4 — verification correction + R3-strengthen + empty-scan fix.**

A second round of 5 verification subagents (commit `ca2db70`) found:

- Eval-log iter 1 OVERSTATED several wins (rounded-int CSV reads vs
  full-precision deltas). Numbers corrected in the table above.
- Several scenarios pick up small id_switches / track_breaks
  regressions not previously mentioned. Added to the table.
- R3 (PSD guard) was INCOMPLETE: the diagonal-positivity check let
  through non-finite/off-diagonal-dominated cases, and the
  `IEstimator::gate` + `logLikelihood` default impls in
  `EstimatorDefaults.cpp` lacked the guard. Iter 4 promotes
  `isMeasurementCovariancePsd` to a full LDLT-based PSD test and
  guards the two default-impl entry points.
- PmbmTracker's empty-scan branch returned early before
  `mergeBernoulliDuplicates` AND before `firePmbmLifecycleEvents`.
  Iter 4 calls both in the empty-scan path too (lifecycle events
  fire on every scan now; re-promotion after an empty-scan
  Tentative emission works correctly).
- Iter 4 bench (not pinned; byte-identical to
  `pmbm_phase8_20260622.csv` on every scenario) confirms iter 4
  fixes are purely defensive — no operational impact, no
  operational regression.

**Iter 5 — adaptive-K birth-id cache.** A subagent diagnosed the
iter 1/3 sc13/sc16 regressions as fragmentation: `next_bernoulli_id_++`
allocates a fresh id per child branch, so under K=5 the same
measurement gets up to 5 distinct ids per parent and the
within-hypothesis merge cannot fold them. Iter 5 implements a
per-(parent_idx, measurement_idx) cache (`scan_birth_id_cache_`)
so all K children of one parent that birth a Bernoulli for the
same measurement share one BernoulliId. Re-measured at K=5:

| Bucket | Iter 5 (id-cache + K=5) vs Phase 8 final (K=1) |
|---|---|
| philos | GOSPA −17.1 % (82 → 68) |
| dense_clutter | GOSPA −15.4 % (13 → 11) |
| autoferry sc4 unanchored | GOSPA −15.4 %, T-GOSPA-raw −14.0 % |
| autoferry sc2/3/6/17 unanchored | -5..-6.5 % |
| autoferry sc13 | GOSPA +6.7 %, T-GOSPA +4.6 % |
| autoferry sc13_anchored | GOSPA +33 %, T-GOSPA +27 % |
| autoferry sc16 unanchored | GOSPA +16.7 %, T-GOSPA +13.9 % |
| autoferry sc16_anchored | GOSPA +33 %, T-GOSPA +25 % |
| autoferry sc17/22 anchored | T-GOSPA +4.3..+8.4 % |

The id-cache is mechanically correct but does NOT unblock adaptive K.
Regressions on sc13/16/22 are essentially unchanged from iter 1
(no cache). The diagnosed root cause is wrong; the real bottleneck
is structural: our flat per-hypothesis Bernoulli list vs MATLAB's
per-track list of single-target hypotheses. Under adaptive K the
existing-Bernoulli assignment columns differ across the K children
of one parent; without per-track-hypothesis bookkeeping the merge
can't distinguish "branch A's interpretation of target B" from
"branch C's interpretation of target B". Verdict: keep
`Config::adaptive_k_best` switch + `scan_birth_id_cache_`
shipped as future-ready scaffolding; bench config stays K=1 until
the per-track-hypothesis refactor lands.

**Files.** Baseline `docs/baselines/pmbm_phase8_20260622.csv`. New
test file `tests/pmbm/test_pmbm_phase8.cpp` (7 tests).

---

## 2026-06-21 (Phase 7, Adaptive Birth — Reuter 2014) — [Cl-3 PMBM Phase 7] decoupled spatial/existence birth: dense_clutter -52 %, philos -16 %, autoferry unanchored -5..-32 %, all anchored T-GOSPA-raw -8..-60 %

**Premise.** Parking-lot item #1 (clutter-aware PPP birth) and item #2
(anchored bias gating) both diagnose the same root cause:
`measurement_driven_birth = true` injects a fresh PoissonComponent
centred on every measurement, then `buildNewTargetCandidates` uses
that just-injected component to compute ρ_target — so
`r_new = ρ_target / (ρ_target + λ_C)` is pegged near 1 for *every*
measurement, including clutter. The textbook fix (Reuter 2014,
"The Labeled Multi-Bernoulli Filter", §IV-B): decouple spatial
birth (mean at z, cov from estimator.initiate) from the existence
prior (configurable scalar `λ_birth` independent of any
measurement). New r_new = `λ_birth / (λ_birth + λ_C(z))`.

**Method — 5-iter polish.** All on `master` (b721c94 → HEAD).

- **Iter 1 (no smart-birth gate).** Added `Config::adaptive_birth`
  + `Config::lambda_birth`, new `buildAdaptiveBirthCandidates`,
  skipped measurement-driven PPP injection under adaptive_birth=true.
  Probe at λ_birth=1e-3: big anchored sc17/sc22 wins (−83 % / −62 %
  GOSPA) BUT all synthetic and unanchored scenarios blew up
  (+27..+100 % GOSPA, id_switches 0→20+). Root cause: without the
  legacy `smart_birth_skip_existing` gate (which lived inside the PPP
  injection block we now skip), every measurement produced an
  adaptive candidate — including those already claimed by a high-r
  Bernoulli. Under K=1 enumeration the new-target row id-flapped
  the existing track.

- **Iter 2 (smart-birth gate ported into adaptive path).**
  Restored synthetic + autoferry-unanchored (sc4 −10.5 % GOSPA,
  several −1..−8 % T-GOSPA-smooth wins). The anchored sc17/sc22
  "wins" from iter 1 disappeared — they were id-switch-driven
  mirage (sc17_anchored id_switches 0→30 in iter 1), not real
  algorithmic improvements. The anchored regression structurally
  needs Schmidt-KF R-inflation post-bias-publish, not adaptive
  birth. Philos still +15 % GOSPA — λ_birth=1e-3 still too
  aggressive.

- **Iter 3 (λ_birth probe on philos only).** Bench-filtered to
  philos. λ_birth=1e-4 (= λ_C, r_new=0.5): +7 % GOSPA.
  λ_birth=1e-5 (r_new≈0.09): **−16 % GOSPA**. Textbook PMBM shape:
  new Bernoullis born small-r, ramp via posterior over subsequent
  detections rather than being pegged near 1 by ρ_target
  contamination.

- **Iter 4 (full bench at λ_birth=1e-5).** Pinned
  `docs/baselines/pmbm_phase7_adapt_20260621.csv`. Headline:

  | Bucket | Adaptive Birth vs legacy PMBM |
  |---|---|
  | dense_clutter | −51.9 % GOSPA (27 → 13), parking-lot #1 closed |
  | philos | −16.3 % GOSPA (98 → 82) |
  | autoferry sc2/4/5/6 unanchored | −9..−32 % GOSPA |
  | autoferry sc13/16/17 unanchored | −6..−8 % GOSPA |
  | autoferry sc2-6 anchored | T-GOSPA-raw −13..−60 % |
  | autoferry sc13/16/22 anchored | T-GOSPA-raw −20..−38 % + id_switches 67→1 / 55→1 / 18→2 |
  | synthetic clean (crossing, head_on, parallel, …) | flat or small wins |
  | regressions | none meaningful (a few 2→3 GOSPA noise on anchored mins) |

- **Iter 5 (commit, eval-log, parking-lot close-out).** This
  entry. `imm_cv_ct_pmbm_adapt` added to the standing config
  list; canonical `imm_cv_ct_pmbm` left for now as the A/B
  reference until external review confirms.

**Takeaway.** Adaptive Birth at λ_birth=1e-5 closes parking-lot item
#1 (dense_clutter / philos) AND incidentally cleans up most
autoferry regressions including the anchored ones. The anchored
id_switch collapse is the most striking secondary effect — under
legacy PMBM the contaminated ρ_target spawned phantom Bernoullis
on every AIS broadcast in anchored mode; adaptive birth's small
initial r lets the existing Bernoulli's update beat the new-target
row in assignment, so the id stays stable. Parking-lot item #2
(Schmidt-KF post-bias R-inflation) is partially superseded by this
result — anchored T-GOSPA-raw is now competitive without the
Schmidt-KF flow.

**Files.** Baseline `docs/baselines/pmbm_phase7_adapt_20260621.csv`.

---

## 2026-06-21 (Phase 6 polish, 5-iter measurement) — [Cl-3 PMBM Phase 6] T-GOSPA wired + RTS measured: wins on noisy / sparse / unanchored, breaks anchored evaluation mode

**Premise.** Phase 4(C) shipped an RTS smoother with the F≈I
approximation. Phase 5 shipped T-GOSPA as the trajectory-aligned
metric. Neither was wired into the bench, so we shipped an
architectural win without measurement. Phase 6 closes the loop:
wire both into the bench output and iterate the smoother until
the measurement tells us where it actually helps.

**Method — 5-iter polish on `feature/cl3-pmbm`.**

- **Iter 1 (47cb76a):** wire T-GOSPA on raw per-scan positions.
  Stitch BenchResult.steps positions keyed by truth_id /
  TrackId.value into time-indexed trajectories, feed through
  TGospa.hpp. New `tgospa_raw` column.

- **Iter 2 (fadcaac):** add `PmbmTracker::collectSmoothedTrajectories()`
  walking the dominant hypothesis and applying
  `rtsSmoothTrajectory` per Bernoulli. New `tgospa_smooth` column.
  PROBE measured: synthetic + noisy scenarios improve (crossing
  −31%, philos −52%), anchored autoferry regress catastrophically
  (sc2_anchored +188%). DIAGNOSIS: F=I makes the smoother collapse
  to "copy end-state backward" for moving targets.

- **Iter 3 (f36eb17):** replace F=I with constant-velocity F
  derived from dt (state layout px, py, vx, vy [, ω]). Smoother
  gain becomes G = P_filt · F^T · P_pred^{-1}. Improves crossing
  further (44.3 → 32.7) but autoferry/philos unchanged — the
  CV F correction only fires on detection scans, and for those
  scenarios the cumulative effect is small relative to other
  trajectory effects.

- **Iter 4:** non_cooperative bug fix — when PMBM emits zero
  tracks, Sweep was falling through to the scalar computeMetrics
  overload, leaving tgospa_smooth at the default 0 sentinel
  (looked like a fake -100% win). Fix: always call the smoothed
  overload for PMBM runs; empty smoothed map now correctly
  produces cardinality penalty.

- **Iter 5 (this entry):** full 29-scenario re-bench, eval log,
  commit, summary.

**Full bench results (pmbm_phase6_full_20260621.csv):**

### Wins (smoothing reduces T-GOSPA by ≥30%):

| Scenario | T-GOSPA raw | smooth | Δ% |
|---|---:|---:|---:|
| dense_clutter | 166.3 | 55.2 | **−67%** |
| philos | 447.6 | 213.1 | **−52%** |
| crossing | 64.1 | 32.7 | **−49%** |
| head_on | 64.1 | 32.7 | **−49%** |
| parallel_targets | 36.1 | 19.6 | **−46%** |
| clock_skew | 29.5 | 16.7 | **−43%** |
| speed_change | 36.2 | 20.9 | **−42%** |
| crossing_dropout | 86.0 | 51.6 | **−40%** |
| ais_dropout | 107.3 | 70.7 | **−34%** |

### Moderate wins (autoferry unanchored, ≤30%):

| Scenario | raw | smooth | Δ% |
|---|---:|---:|---:|
| autoferry_scenario22 | 699.8 | 584.5 | −16% |
| autoferry_scenario3 | 944.8 | 838.6 | −11% |
| autoferry_scenario5 | 1081.7 | 992.8 | −8% |
| autoferry_scenario2 | 856.9 | 788.4 | −8% |
| autoferry_scenario6 | 838.3 | 772.3 | −8% |
| autoferry_scenario4 | 749.3 | 724.4 | −3% |

### Regressions:

| Scenario | raw | smooth | Δ% |
|---|---:|---:|---:|
| autoferry_scenario17 | 531.8 | 557.5 | +5% |
| autoferry_scenario13 | 589.3 | 678.8 | +15% |
| autoferry_scenario16 | 517.5 | 679.4 | +31% |
| overtaking | 48.3 | 67.0 | +39% |
| **autoferry_sc17_anchored** | 383.5 | 550.3 | **+44%** |
| **autoferry_sc22_anchored** | 356.3 | 580.7 | **+63%** |
| **autoferry_sc16_anchored** | 279.3 | 675.9 | **+142%** |
| **autoferry_sc13_anchored** | 272.0 | 675.7 | **+148%** |
| **autoferry_sc6_anchored** | 307.3 | 767.3 | **+150%** |
| **autoferry_sc2_anchored** | 271.7 | 783.1 | **+188%** |
| **autoferry_sc4_anchored** | 207.8 | 718.1 | **+246%** |
| **autoferry_sc3_anchored** | 240.4 | 833.3 | **+247%** |
| **autoferry_sc5_anchored** | 258.0 | 988.2 | **+283%** |

### Analysis

**RTS smoothing as default-on is NOT safe.** All 9 anchored
variants regress catastrophically. The mechanism is consistent
and structural: anchored evaluation mode injects AIS positions
as "truth" so the filter posterior at AIS-touch scans becomes
extremely tight, while intervening multi-sensor scans (radar /
EO/IR) have looser posteriors. The RTS gain `G = P_filt ·
F^T · P_pred^{-1}` ≈ identity for adjacent tight-then-loose
scans (since P_pred ≈ P_filt with small Q), causing the smoother
to fully blend in the future scan's noise back into the past
scan's near-perfect estimate.

**RTS smoothing on real workloads is a clear win.** All 9 clean
synthetics + philos + dense_clutter improve by 34-67%. 6 of 10
autoferry unanchored variants improve by 3-16%. 4 unanchored
variants regress modestly (5-39%) — these are the scenarios
where some scans still carry AIS positions even without explicit
anchoring (real ferry traffic has AIS).

**Anchored mode is a test scaffolding artifact** — it forces
the filter to treat AIS as truth specifically to isolate
tracking-pipeline errors from registration errors. The RTS
smoother is fighting that test mode, not real deployment.

### What to test next

- **(parked) Per-mode IMM RTS** — current CV F is exact for
  CV motion but loses ω-coupling on CT. Implementing per-mode F
  weighted by mode probabilities would tighten the smoother but
  doesn't address the structural anchored issue.
- **(parked) Q-aware smoother** — inflating the smoother's
  effective P_pred (vs filter's P_pred) would downweight loose
  future evidence vs tight past, reducing the anchored regression.
  This is the right structural fix; out of scope here.
- **(deployment guidance)** — enable `trajectory_window_scans > 0`
  for the regular bench config (which is what we have).
  Anchored evaluation runs should disable RTS smoothing OR consume
  `tgospa_raw` instead of `tgospa_smooth`. Document this.

### Phase 6 polish — verdict

The TPMBM stack (4(A)/4(B)/4(C)/4(D)) + Phase 5 T-GOSPA + Phase 6
bench wiring forms a coherent measurement-driven trajectory layer.
On the deployment-relevant axis (autoferry unanchored + noisy
real-world scenarios), RTS smoothing improves T-GOSPA by 3-67%.
The anchored-mode regression is a known limitation of the current
smoother formulation; the structural fix (Q-aware smoothing) is
parked, with deployment guidance to use `tgospa_raw` for anchored
evaluation.

## 2026-06-21 (Phase 4(C) + 4(D) + Phase 5) — [Cl-3 PMBM] TPMBM story complete: trajectory snapshot, T-GOSPA, RTS smoother

**Premise.** Finish the Phase 4 (TPMBM) story:
- 4(C) backward RTS smoothing
- 4(D) trajectory-on-Deleted snapshot
- Phase 5 T-GOSPA metric (the only metric that can actually
  MEASURE trajectory-coherence wins from 4(C))

Ordering matters: 4(C) without Phase 5 is dead code (per-scan
GOSPA can't see past states), so Phase 5 came first.

**Phase 4(D) — trajectory-on-Deleted snapshot (commit 56c82e5).**
`firePmbmLifecycleEvents` now snapshots trajectories from the
current dominant hypothesis at the end of each scan, keyed by
Bernoulli id. `trajectoryFor(id)` falls back to that snapshot
when the id is not in any live hypothesis — so `onTrackDeleted`
handlers calling `tracker.trajectoryFor(event.id.value)` get the
final trajectory before it would otherwise be lost to pruning.
Snapshot cleared and refreshed each scan; zero overhead when no
sink wired.

**Phase 5 — T-GOSPA metric (commit dd6d1d2).**
`core/scenario/TGospa.hpp` + `core/scenario/TGospa.cpp`.
Operates on time-indexed `Trajectory{id, samples: map<int, pos>}`:

  T-GOSPA(X, Y; c, p, γ) = ( Σ_k GOSPA_k + γ^p · #switches )^(1/p)

Per-scan assignment via Hungarian on the same augmented matrix
shape as `Gospa.cpp`; switching penalty applied between adjacent
scans by comparing matched truth→est ids. Greedy per-scan optimal
+ sum-over-time is the "approximate T-GOSPA" — the LP-relaxed
formulation gives a tighter bound but adds a solver dependency.
6 focused tests cover empty, identical, per-scan-error
accumulation, switch penalty, missed-truth and false-est
cardinality.

**Phase 4(C) — RTS smoothing (this entry).**
`rtsSmoothTrajectory(std::vector<TrajectoryPoint>&)` in
PmbmTracker.cpp. Backward pass per the textbook:

  G_k = P_filt_k · F_k^T · P_pred_{k+1}^{-1}
  x_smooth_k = x_filt_k + G_k · (x_smooth_{k+1} − x_pred_{k+1})
  P_smooth_k = P_filt_k + G_k · (P_smooth_{k+1} − P_pred_{k+1}) · G_k^T

`TrajectoryPoint` extended with `predicted_state` /
`predicted_covariance` so the backward pass is stateless w.r.t.
the filter run. `appendTrajectoryPoint` captures the pre-update
(post-predict) state from the parent Bernoulli at every call
site — birth, detection, misdetection, empty-scan misdetection.

**Approximation.** F_k ≈ I. Exact for stationary targets; biased
(position-velocity cross-terms lost) for moving targets. The
covariance-weighted blend `G ≈ P_filt · P_pred^{-1}` still does
useful work — past states get pulled toward future observations
weighted by relative uncertainty — but the magnitude of correction
is conservative for moving targets. **Real fix:** extend
`IEstimator` with `transitionMatrix(track, t)`; pass per-step F
through. Out of scope this session; documented in the smoother
header.

**Tests (PmbmTrackerUpdate.Rts*, 3 cases):**
- RtsSmoothNoOpOnShortTrajectory (empty + single-point are no-ops)
- RtsSmoothShrinksCovarianceOnStationaryTrajectory (covariance
  doesn't inflate on a no-information stationary trajectory)
- RtsSmoothPullsPastTowardFutureUpdate (numerical: σ²=4 at k=0,
  4 m position jump at k=1 → smoothed at k=0 lands at 4 m, as the
  Kalman gain formula predicts)

**Bench impact.** Not measured. Per-scan GOSPA can't see past
states, and the RTS pass is not wired into the bench
emit-trajectories path. To validate the wins on autoferry, we'd
need to: (a) run PMBM with TPMBM enabled, (b) call
`rtsSmoothTrajectory` on the emitted trajectory per id,
(c) score with T-GOSPA against truth trajectories. That bench
wiring is Phase 6.

**722 → 732 tests, all pass** (+6 T-GOSPA, +1 4(D), +3 4(C)).

**TPMBM story status:**
- 4(A) ✅ trajectory bookkeeping (b3cb89b)
- 4(B) ✅ ITrackSink wiring (232bbcb)
- 4(C) ✅ RTS smoothing (this commit, with F≈I approximation)
- 4(D) ✅ trajectory-on-Deleted snapshot (56c82e5)
- Phase 5 ✅ T-GOSPA metric (dd6d1d2)
- **Phase 6 (deferred)**: wire RTS + T-GOSPA into bench so the
  TPMBM wins on autoferry are quantitatively measured.

## 2026-06-21 (Phase 4(B)) — [Cl-3 PMBM Phase 4(B)] ITrackSink wiring on PmbmTracker: push-based lifecycle events

**Premise.** Phase 4(A) added per-Bernoulli trajectory recording
and the `trajectoryFor(id)` pull accessor; Phase 4(B) completes
the operator-facing interface by firing
`onTrackInitiated/Confirmed/Updated/Deleted` from PMBM each scan
(matching MhtTracker semantics through TrackManager).

**Method.** Three additive changes:

- `PmbmTracker::setTrackSink(ITrackSink*)` + `track_sink_`
  member + `prev_emitted_statuses_` map (prior-scan emitted
  TrackId → status).
- `firePmbmLifecycleEvents(scan_time)` diffs current
  `tracks()` against `prev_emitted_statuses_`:
  - new id Tentative → `onTrackInitiated`
  - new id Confirmed → `onTrackInitiated` + `onTrackConfirmed`
    (single-scan birth-and-confirm path)
  - prior Tentative → current Confirmed → `onTrackConfirmed`
  - every present-this-scan id → `onTrackUpdated`
  - prior id absent now → `onTrackDeleted` (pre-snapshot
    status reported)
- Wired into `processBatch` end. No-op when no sink wired (null
  default; pull-only mode remains bit-identical to Phase 4(A)).

Trajectory consumption: callbacks can call
`tracker.trajectoryFor(event.id.value)` inside the handler;
the dominant hypothesis is still live at that point. For
`onTrackDeleted` the trajectory is gone (pruned) — Phase 4(C)
candidate: snapshot trajectory before prune so deleted events
can carry it.

**Tests.** `TrackSinkFiresInitiatedAndConfirmedOnHighRBirth`,
`TrackSinkFiresDeletedWhenExistenceFallsBelowFloor`. All 722
tests in the suite pass.

**What this unlocks.** PMBM is now plug-compatible with any
existing `ITrackSink` consumer (BenchSink, logger, UI). The
push-vs-pull choice is now consumer-driven; the tracker is no
longer pull-only.

## 2026-06-21 (Phase 4 TPMBM increment 1) — [Cl-3 PMBM Phase 4(A)] forward-pass trajectory per Bernoulli: foundation for TPMBM, zero bench regression

**Premise.** Plan doc Phase 3 (our Phase 4) calls for Trajectory
PMBM (TPMBM, García-Fernández/Williams/Granström/Svensson 2020,
arXiv:1912.08718): per-Bernoulli state HISTORY, smoothing through
the trajectory, T-GOSPA metric, ITrackSink-driven lifecycle. Full
TPMBM is a multi-week effort (RTS smoothing, trajectory-level
pruning, new metric). This entry covers the first increment —
forward-pass bookkeeping — which is the necessary scaffold for
everything else and gives operator-visible track history at zero
algorithmic cost.

**Method.** Three additive changes in `feature/cl3-pmbm`:

- `TrajectoryPoint` type in `core/pmbm/PmbmTypes.hpp` (time, state,
  covariance). `Bernoulli` extended with `birth_time` and
  `std::vector<TrajectoryPoint> trajectory`. Default-empty —
  zero-overhead when `Config::trajectory_window_scans = 0`.
- `appendTrajectoryPoint` helper called at three points in
  `enumerateChildren`: post-update (detection branch),
  post-predict (regular and empty-scan misdetection branches),
  and on new-target row materialisation. Truncates to the most
  recent N points per the window config.
- Public accessor
  `PmbmTracker::trajectoryFor(BernoulliId) const` returns the
  dominant (highest-weight) hypothesis's trajectory for that id.
  Empty when id is unknown or TPMBM disabled.

Bench (config knob ON, `trajectory_window_scans = 50`): 4-scenario
probe (philos, autoferry_scenario2/22, non_cooperative, crossing,
crossing_dropout) shows bit-identical GOSPA / id_switches /
lifetime vs Phase 3 baseline — expected because trajectory
recording is purely additive bookkeeping (no path reads trajectory
back into the tracker math).

### What this unlocks

- **Operator UX** — `onTrackDeleted` consumers (when ITrackSink is
  wired into PMBM, Phase 4(B)) can now emit the full per-target
  path, not just the final state.
- **RTS smoothing** — the trajectory stores per-point (state, cov)
  which is enough for a backward Rauch-Tung-Striebel pass once
  transition matrices are also stored. Phase 4(C) candidate.
- **T-GOSPA metric** — trajectory-time-aligned variant of GOSPA;
  needs trajectory access to compute. Per plan doc Phase 4 (our
  Phase 5).

### What to test next

- **Phase 4(B): ITrackSink wiring** — fire
  `onTrackConfirmed/Updated/Deleted` from PMBM, carry trajectory
  on Deleted. Requires `setTrackSink` on PmbmTracker and a
  per-scan diff against the previous-scan track set.
- **Phase 4(C): RTS smoothing** — store per-scan state transition
  on TrajectoryPoint (or augment Bernoulli with a parallel
  transition history). Re-runs the trajectory backward at each
  update so past states get the benefit of future measurements.
  Expected GOSPA win on autoferry (smoother trajectories →
  lower per-point error). Whether to gate via window or every
  scan is the parameter.
- **Phase 5: T-GOSPA metric.** Pull GOSPA out of `Ospa.hpp`,
  add trajectory-time alignment. Reproduces published TPMBM
  comparisons.

## 2026-06-21 (Phase 3 polish) — [Cl-3 PMBM Phase 3] idle-decay + phantom-birth gate: non_cooperative wins (−28 %), PMBM now beats MHT on 23 / 29 scenarios

**Premise.** Phase 2 close-out left three named gaps and proposed
two targeted polish knobs:
- `philos +43 %` → idle-decay on Bernoullis whose contributing
  sources are absent from a scan (ghost-track flush).
- `dense_clutter +138 %` → phantom-birth gate at low `r_new`
  (suppress near-zero existence births).
- `sc17/sc22 anchored` → bias-correction interaction (deferred).

**Method.** Three additive commits on `feature/cl3-pmbm`:

- **(A) `idle_halflife_sec`** (PmbmTracker::Config). When
  source_aware_misdetection skips the recursion (or no sensor
  covers the Bernoulli at all) the existence used to be frozen.
  New path: `r ← r · exp(−ln 2 · Δt / halflife)` where Δt is the
  time since the Bernoulli's most-recent SourceTouch
  (contribution_history). Real targets re-touched every AIS scan
  reset the decay; ghosts decay below `r_min` in ≈ N·halflife
  with bench value `halflife = 10 s` (N ≈ 7).
- **(B) `min_new_bernoulli_existence`** (PmbmTracker::Config).
  Phantom-birth gate in `enumerateChildren` new-target row:
  when `r_new = ρ_target/ρ_total < threshold` the Bernoulli is
  not materialised but the assignment cell still consumes the
  clutter mass (Murty stays balanced). Bench value 0.5 (real
  targets have `r_new ≈ 1` under any reasonable PPP coverage,
  so the gate never blocks legitimate births).
- **(C) PPP-coverage gate** (`smart_birth_skip_existing_ppp`,
  off in bench config). Implemented and unit-tested, but the
  measurement-axis A/B (4 thresholds: 1e-4, 1e-5, 1e-6, 3e-6)
  showed best case `philos −4.4` at the cost of
  `autoferry_scenario4_anchored +2.3` — the gate also suppresses
  legitimate re-birth in tight, bias-corrected anchored cases.
  Kept as a knob for future experimentation; the real fix for
  the philos/dense_clutter contamination requires Reuter (2014)
  Adaptive Birth Distribution (decouple spatial birth from
  existence prior) — parked, see
  `docs/superpowers/plans/2026-06-07-pmbm-integration-plan.md`.

Full 29-scenario × seed 0 re-bench:
`./build/bench/navtracker_bench_baseline --seeds 1
--run-id pmbm_phase3_rebench_20260621`. Pinned:
`docs/baselines/pmbm_phase3_rebench_20260621.csv`. Diff against
Phase 2 baseline (the prior PMBM floor).

### Headline — GOSPA, MHT canonical vs PMBM-P2 vs PMBM-P3

| Scenario | MHT | P2 | **P3** | Δ vs P2 | Δ vs MHT |
|---|---:|---:|---:|---:|---:|
| **non_cooperative** | 19.85 | 19.71 | **14.14** | **−5.57** | **−29 %** |
| autoferry_scenario4 | 31.94 | 20.45 | **19.40** | −1.04 | **−39 %** |
| autoferry_scenario3 | 35.94 | 22.02 | 21.78 | −0.24 | **−39 %** |
| autoferry_scenario6 | 30.55 | 20.76 | 20.57 | −0.19 | **−33 %** |
| autoferry_scenario16 | 25.79 | 13.77 | 13.70 | −0.06 | **−47 %** |
| autoferry_scenario5 | 33.49 | 21.07 | 21.01 | −0.06 | **−37 %** |
| autoferry_scenario2 | 33.28 | 20.07 | 20.01 | −0.06 | **−40 %** |
| autoferry_scenario22 | 36.87 | 22.39 | 22.37 | −0.02 | **−39 %** |
| autoferry_scenario17 | 25.20 | 17.51 | 17.50 | −0.01 | **−31 %** |
| autoferry_scenario13 | 21.49 | 15.17 | 15.17 | parity | **−29 %** |
| philos | 69.43 | 99.23 | 98.91 | −0.32 | +42 % |
| dense_clutter | 10.91 | 25.96 | 25.82 | −0.13 | +137 % |
| (clean synthetics × 9, anchored × 9) | … | … | parity | parity | unchanged |

### Score: PMBM-P3 wins or matches MHT on 23 of 29 scenarios (+1 vs P2)

**Decisively beats MHT (≥ 20 % GOSPA improvement):**
- All 9 autoferry unanchored (−29 to −47 %)
- 3 anchored (sc5/6/13)
- **non_cooperative (−29 %)** — new in P3

**Remaining gaps (unchanged from P2):**
- philos +42 %, dense_clutter +137 % — both driven by the
  same measurement-driven-birth contamination (the just-injected
  PPP component dominates `ρ_target` for its own measurement,
  inflating `r_new` regardless of clutter density).
- sc17/sc22 anchored — bias-correction interaction with the
  fixed χ² = 9 gate.

### What to test next

- **TPMBM (Phase 4 of this session, Phase 3 in the plan doc).**
  Trajectory-PMBM: per-Bernoulli state history, smoothing back
  through history, better id stability when targets pass close.
  Standard literature next step (García-Fernández/Williams 2020).
- **Reuter (2014) Adaptive Birth Distribution.** The real fix
  for philos/dense_clutter — decouple spatial birth from
  existence prior. Parked behind TPMBM (the autoferry wins
  matter more for deployment than philos/dense_clutter parity).

## 2026-06-21 (later) — [Cl-3 PMBM Phase 2 close-out] ISensorDetectionModel + per-mode IMM birth: PMBM beats MHT on 22 / 29 scenarios, including all 9 autoferry unanchored

**Premise.** Phase 1.5 close-out left three gaps: (1) sc13/16/17
unanchored +20-40 % over MHT (clutter/sensor interactions); (2)
dense_clutter +159 %; (3) anchored 2.5-7× over MHT. Diagnosis
across all three pointed at the same root cause — PMBM was using
a single global P_D / λ_C instead of the scenario's per-sensor
detection table that MhtTracker has been driving since the
multi-sensor work landed in May.

**Method.** Two additive commits on `feature/cl3-pmbm`:

- (A) `PmbmTracker::setSensorDetectionModel(ISensorDetectionModel)`.
  Replaces global `cfg.probability_of_detection` and
  `cfg.clutter_intensity` with per-(sensor, model, source_id)
  lookups in three call sites: `buildNewTargetCandidates`
  (per-measurement ρ_target / ρ_total), the cost-matrix detection
  log-weight, and the per-Bernoulli misdetection recursion. The
  misdetection p_D is aggregated across in-coverage scan sensors via
      `miss_pD = 1 − Π_s (1 − missDetectionProbability_s)`
  with `missDetectionProbability = 0` outside the sensor's
  `max_range` / `sector` — so a Bernoulli outside every scan
  sensor's coverage gets zero penalty (correct for sparse async AIS
  scans). Sweep wires the scenario's table to PMBM via the same
  `detectionModelFor` helper as the MHT path.

- (B) Per-mode IMM-mixture moment-match at PMBM birth. The Phase 1.5
  `NewTargetCandidate` took its `imm_*` fields from the DOMINANT
  PPP component (dominant-component approximation, exact only when
  one component contributed). Phase 2 weights per IMM mode `j` by
  `w_i · μ_i[j]` across all post-update components and moment-
  matches the per-mode mean / cov / mode-prior. Polish given that
  smart birth usually gives a single contributor; principled
  replacement for the eventual multi-component PPP case.

Full 29-scenario × seed 0 re-bench:
`./build/bench/navtracker_bench_baseline --seeds 1
--run-id pmbm_phase2_rebench_20260621`. Pinned:
`docs/baselines/pmbm_phase2_rebench_20260621.csv`. Diff against
the MHT canonical + Phase 1 + Phase 1.5 baselines.

### Headline — GOSPA, MHT canonical vs PMBM-P1 vs PMBM-P1.5 vs PMBM-P2

| Scenario | MHT | P1 | P1.5 | **P2** | Δ vs MHT |
|---|---:|---:|---:|---:|---:|
| **autoferry_scenario22** | 36.87 | 42.29 | 34.88 | **22.39** | **−39 %** |
| **autoferry_scenario3**  | 35.94 | 20.85 | 21.76 | **22.02** | **−39 %** |
| **autoferry_scenario2**  | 33.28 | 22.05 | 22.55 | **20.07** | **−40 %** |
| **autoferry_scenario5**  | 33.49 | 20.88 | 23.57 | **21.07** | **−37 %** |
| **autoferry_scenario4**  | 31.94 | 14.77 | 16.53 | **20.45** | **−36 %** |
| **autoferry_scenario6**  | 30.55 | 18.87 | 19.04 | **20.76** | **−32 %** |
| **autoferry_scenario16** | 25.79 | 46.00 | 31.25 | **13.77** | **−47 %** |
| **autoferry_scenario17** | 25.20 | 44.84 | 31.56 | **17.51** | **−30 %** |
| **autoferry_scenario13** | 21.49 | 42.08 | 29.69 | **15.17** | **−29 %** |
| autoferry_scenario13_anchored | 3.12 | 26.82 | 7.61 | **2.44** | **−22 %** |
| autoferry_scenario5_anchored | 3.06 | 6.88 | 5.30 | **2.28** | **−26 %** |
| autoferry_scenario6_anchored | 5.60 | 5.11 | 8.17 | **3.74** | **−33 %** |
| autoferry_scenario2_anchored | 2.34 | 6.84 | 7.93 | 2.92 | +25 % |
| autoferry_scenario3_anchored | 1.54 | 4.60 | 4.36 | 2.45 | +59 % |
| autoferry_scenario4_anchored | 2.64 | 1.50 | 2.89 | 2.67 | +1 % (parity) |
| autoferry_scenario16_anchored | 2.35 | 27.61 | 17.39 | 2.85 | +21 % |
| autoferry_scenario17_anchored | 2.63 | 23.12 | 15.63 | 12.17 | +363 % |
| autoferry_scenario22_anchored | 3.42 | 17.75 | 16.93 | 8.18 | +139 % |
| crossing | 9.86 | 15.06 | 14.60 | **9.55** | **−3 %** |
| head_on | 9.86 | 15.04 | 14.60 | **9.55** | **−3 %** |
| overtaking | 6.23 | 9.76 | 6.15 | **5.97** | **−4 %** |
| parallel_targets | 6.89 | 10.76 | 6.34 | **6.34** | **−8 %** |
| speed_change | 5.24 | 6.54 | 5.38 | **5.04** | **−4 %** |
| clock_skew | 4.23 | 6.67 | 3.99 | **4.03** | **−5 %** |
| crossing_dropout | 12.30 | 16.74 | 16.54 | **11.99** | **−2 %** |
| ais_dropout | 15.18 | 18.76 | 20.48 | **14.85** | **−2 %** |
| non_cooperative | 19.85 | 19.85 | 19.85 | 19.71 | parity |
| dense_clutter | 10.91 | 32.47 | 28.30 | 25.96 | +138 % |
| philos | 69.43 | 63.65 | 67.62 | 99.23 | **+43 %** (regression) |

### Score: PMBM-P2 wins or matches MHT on 22 of 29 scenarios

**Decisively beats MHT (≥ 20 % GOSPA improvement):**
- all 9 autoferry unanchored (sc2/3/4/5/6/13/16/17/22), −29 to −47 %
- 3 anchored (sc5/6/13), −22 to −33 %

**Matches MHT (±10 %):**
- All 9 clean synthetics (crossing, head_on, overtaking,
  parallel_targets, speed_change, clock_skew, crossing_dropout,
  ais_dropout, non_cooperative)
- 4 anchored (sc2, sc4, sc16) — +1-25 %

**Still worse than MHT:**
- philos +43 % (regression from P1.5; lifetime went 0.005 → 0.429
  but cardinality bloated under the looser misdetection)
- dense_clutter +138 % (still doesn't handle high clutter
  density well; smart birth gate admits too many phantom births)
- autoferry_scenario17_anchored +363 %, sc22_anchored +139 % (id
  flapping resurged on these specific anchored variants — see
  diagnosis below)

### What happened to id_switches

Total scan-summed id_switches across the 29 scenarios:
P1.5 ≈ 320 → P2 ≈ 530 (regression). Concentrated on the anchored
variants where bias correction shrinks the measurement-prediction
spread and the smart-birth gate (χ²=9) admits adjacent fresh
births. Mostly cosmetic — most of those switches show as small
absolute id_sw increases on anchored runs that still GOSPA-win
(e.g. sc13_anchored: id_sw 1 → 67 but GOSPA 7.6 → 2.4). Worth
tightening the smart-birth gate or scaling it by the bias-
corrected R magnitude — Phase 3 polish.

### Why philos regressed

Before P2(B), the source-aware misdetection guard kept Bernoullis
alive across vessel-foreign broadcasts but the absent per-sensor
coverage still let irrelevant ghosts die. Wiring the detection
model + per-coverage `miss_pD` = 0 outside the AIS sender's
coverage means Bernoullis now live indefinitely until a vessel-
specific broadcast lifts r above `confirm_threshold = 0.5` AND a
mismatch finally kills them. On philos with O(50+) tracked
vessels that drift out of broadcast for minutes at a time, every
"could exist somewhere out there" Bernoulli stays Tentative-to-
Confirmed and inflates cardinality. The fix is a *time-decay* or
*age-out* on Bernoullis with no recent contribution — pure
existence Bayes can't infer "stopped reporting".

### Takeaway

**Phase 2 is a structural breakthrough.** PMBM now beats the
canonical IMM+MHT stack on every single autoferry *unanchored*
scenario (29-47 % GOSPA improvement) — these are the most
realistic deployment scenarios in the bench (real Trondheim ferry
traffic, multi-sensor, no AIS anchor cheat). On clean synthetics
it matches MHT to within ±5 %. On 3 of 9 anchored variants it
beats MHT outright; on the rest it's within 25 % parity except
sc17_anchored and sc22_anchored (id-flap residual).

The two outstanding gaps — philos +43 %, dense_clutter +138 % —
are characterised and have named fixes (time-decay on stale
Bernoullis for philos; clutter-density-scaled birth gate for
dense_clutter). Both are Phase 3 polish, not structural.

`pmbm_phase2_rebench_20260621.csv` is the new floor. Cl-3 PMBM is
now the better tracker on the bench's representative scenarios.
Phase 3 candidates: time-decay / age-out, clutter-density-scaled
birth gate, TPMBM trajectory extension.

## 2026-06-21 — [Cl-3 PMBM Phase 1.5 close-out] Smart birth + within-id merge + bias wiring + source-aware misdetection: id-flap killed, anchored gap partially closed, Cl-2 #2 wins preserved

**Premise.** The 2026-06-20 first A/B (immediately below) shipped the
structural Cl-2 #2 win but flagged three implementation gaps that
inflated everything else: (1) measurement-driven birth without
clutter gating → 100-170 id_switches per autoferry scenario; (2)
no SensorBiasEstimator wiring → AIS-anchored variants 5-11×
worse; (3) per-vessel misdetection on sparse-broadcast AIS →
philos lifetime collapse 0.31 → 0.005. Phase 1.5 ships fixes for
all three.

**Method.** Three additive PRs on `feature/cl3-pmbm`:
- (1) Smart birth (Reuter 2014 ABD) + within-hypothesis
  Bernoulli merging by Bhattacharyya distance. Skip birth at
  measurements already explained by an existing r ≥ 0.5
  Bernoulli; merge near-duplicate Bernoullis keeping the older
  id.
- (2) `PmbmTracker::setSensorBiasProvider` + per-Bernoulli
  contribution_history (SourceTouch rolling window). Wired into
  the bench Sweep with the same hook shape as MhtTracker, so the
  imm_cv_ct_pmbm config now does AIS-anchored / bearing /
  cross-sensor pair extraction → bias-estimator observe →
  Schmidt-KF measurement correction on subsequent scans.
- (3) Source-aware misdetection (Config::source_aware_misdetection):
  skip the misdetection recursion when none of the Bernoulli's
  contributing source_ids appears in this scan. Brand-new
  Bernoullis still decay normally.

Full 29-scenario × seed 0 re-bench:
`./build/bench/navtracker_bench_baseline --seeds 1
--run-id pmbm_phase1_5_rebench_20260621`. Pinned:
`docs/baselines/pmbm_phase1_5_rebench_20260621.csv`. Compared
against the same MHT canonical and the first-A/B PMBM run.

### Headline — GOSPA, MHT canonical vs PMBM P1 vs PMBM P1.5

| Scenario | MHT | PMBM-P1 | **PMBM-P1.5** | Δ vs MHT | id_sw P1 → P1.5 |
|---|---:|---:|---:|---:|---:|
| **autoferry_scenario4** | 31.94 | 14.77 | **16.53** | **−48 %** | 45 → 5 |
| **autoferry_scenario3** | 35.94 | 20.85 | **21.76** | **−39 %** | 119 → 6.5 |
| **autoferry_scenario5** | 33.49 | 20.88 | **23.57** | **−30 %** | 168 → 3.5 |
| **autoferry_scenario2** | 33.28 | 22.05 | **22.55** | **−32 %** | 85 → 13 |
| **autoferry_scenario6** | 30.55 | 18.87 | **19.04** | **−38 %** | 72.5 → 38.5 |
| autoferry_scenario22 | 36.87 | 42.29 | **34.88** | **−5 %** | 119 → 85 |
| autoferry_scenario13 | 21.49 | 42.08 | 29.69 | +38 % | 153 → 43.5 |
| autoferry_scenario16 | 25.79 | 46.00 | 31.25 | +21 % | 143 → 51.5 |
| autoferry_scenario17 | 25.20 | 44.84 | 31.56 | +25 % | 136.5 → 23.5 |
| autoferry_scenario13_anchored | 3.12 | 26.82 | **7.62** | +144 % (was +759 %) | 42 → 1 |
| autoferry_scenario16_anchored | 2.35 | 27.61 | 17.39 | +639 % (was +1074 %) | 61 → 0.5 |
| autoferry_scenario17_anchored | 2.63 | 23.12 | 15.63 | +495 % (was +780 %) | 62 → 0 |
| autoferry_scenario22_anchored | 3.43 | 17.75 | 16.93 | +395 % (was +418 %) | 44.5 → 0 |
| autoferry_scenario{2,3,4,5,6}_anchored | (1.5–5.6) | (1.5–6.9) | (2.9–8.2) | near-parity (≤ 3.4×) | (0–30) → (0–1.5) |
| dense_clutter | 10.91 | 32.47 | 28.30 | +159 % | 36 → 2 |
| philos | 69.43 | 63.65 | 67.62 | **−3 %** | 0 → 0 |
| crossing / head_on | 9.86 | 15.06 | 14.60 | +48 % | 38 → 0 |
| overtaking / parallel_targets / speed_change / clock_skew / crossing_dropout / ais_dropout | (4–15) | (6–19) | **(4–20)** — most at parity | (−6 % to +35 %) | (21–57) → (0–1.5) |
| non_cooperative | 19.85 | 19.85 | 19.85 | 0 % | 0 → 0 |

### What worked

1. **Cl-2 #2 structural win preserved AND id-flap killed.** All
   five Phase-1 winners (autoferry sc2–sc6 unanchored) remain
   −30 % to −48 % below MHT GOSPA, AND their id_switches drop to
   MHT-comparable levels (sc3: 119 → 6.5; sc5: 168 → 3.5). This is
   the headline pass criterion.
2. **Clean synthetics back to MHT parity.** crossing/head_on
   still carry a residual cardinality cost (PMBM emits one extra
   Tentative-ish track occasionally), but overtaking,
   parallel_targets, speed_change, clock_skew, ais_dropout,
   crossing_dropout all land within ±15 % of MHT GOSPA with
   id_switches at 0.
3. **Anchored variants partially closed.** Worst case
   (sc16_anchored) went 1074 % → 639 %; sc13_anchored 759 % →
   144 %; sc17_anchored 780 % → 495 %; sc22_anchored 418 % →
   395 %. Bias-provider wiring helped, but the bias estimator
   needs more anchored pairs to converge fully — see Phase 2
   below.
4. **id_switches massively reduced everywhere.** Total scan-summed
   id_switches across the 29 scenarios: P1 ≈ 1450 → P1.5 ≈ 320
   (factor 4.5 reduction). Smart birth is the dominant
   contributor.
5. **autoferry_scenario22 now beats MHT** (34.88 vs 36.87 GOSPA).

### What remained

1. **autoferry sc13/sc16/sc17 unanchored** still +20 to +40 %
   over MHT GOSPA. These scenarios involve more challenging
   clutter / multi-sensor interactions. Phase 2's full
   IMM-per-Bernoulli mixture (currently we use ImmEstimator as
   inner but the Bernoulli's spatial density is single-Gaussian)
   should help on the manoeuvring portions.
2. **dense_clutter still +159 %** (28.30 vs 10.91). The
   smart-birth gate (r ≥ 0.5) admits more birth than ideal under
   high clutter rates. Phase 2 candidate: scale the gate by the
   per-sensor estimated clutter density.
3. **anchored variants still 2.5–7× over MHT.** Bias estimator is
   wired but not yet at parity. Probable cause: PMBM's aggregated
   Track loses the per-hypothesis bias signal that the MHT path
   benefits from. Worth a focused investigation in Phase 2.
4. **philos lifetime 0.005 → 0.005** (source-aware misdetection
   didn't move it). The GOSPA is comparable (67 vs 69), which
   tells us PMBM tracks accurately when it tracks; the lifetime
   metric is dominated by truth IDs that PMBM never lifts above
   confirm_threshold = 0.5. Needs proper per-sensor coverage
   modelling (ISensorDetectionModel wiring) to be addressed
   structurally.

### Takeaway

Phase 1 of Cl-3 PMBM is **structurally complete** per the gate
criterion ("Cl-2 #2 wins survive AND id_switches near MHT levels
AND most regressions closed"). The remaining gaps are *bounded
implementation polish*, not algorithmic doubts. The Cl-3 design
predicted the Cl-2 #2 fix and delivered it (−30 to −48 %); the
ID flapping was a phase-1 birth-model artefact, not a PMBM
problem.

`pmbm_phase1_5_rebench_20260621.csv` is the Phase 1 floor. Phase 2
(full IMM-per-Bernoulli mixture as the Bernoulli's spatial
density, currently single-Gaussian moment-match) starts next.

## 2026-06-20 (later) — [Cl-3 PMBM Phase 1, first A/B] Structural win on the Cl-2 #2 pain scenarios; per-clutter id-flap dominates everything else

**Premise.** Cl-3 endgame validation: does GM-PMBM (single-Gaussian
per Bernoulli, IMM as the inner per-mode estimator) beat IMM+MHT on
the 29-scenario bench, in particular on the Cl-2 #2 over-confidence
cases (autoferry sc2-sc6 unanchored) where the design predicts a
structural fix?

**Method.** Wire `imm_cv_ct_pmbm` as a sibling to `imm_cv_ct_mht`
with matched (P_D = 0.9, λ_C = 1e-4, χ² gate = 9) and the same
ImmEstimator (CV5 + CT, UKF inner). Differences against MHT:
no SensorBiasEstimator on the PMBM path; no within-id Bernoulli
merging (§3.5 of `docs/algorithms/pmbm-design.md` — deferred to
Phase 1.5); measurement-driven birth at 0.3 per scan; Murty K=1.
Full 29-scenario × seed 0 matrix run via
`./build/bench/navtracker_bench_baseline --seeds 1 --run-id
pmbm_phase1_first_ab_20260620`. Pinned:
`docs/baselines/pmbm_phase1_first_ab_20260620.csv`. Compared
against `docs/baselines/cl26_canonical_postukf_20260620.csv` (the
post-UKF + post-bias-overconfidence-fix MHT canonical from earlier
this day).

### Headline numbers — GOSPA, PMBM vs MHT canonical

| Scenario | MHT | PMBM | Δ | Δ% |
|---|---:|---:|---:|---:|
| **autoferry_scenario2** (Cl-2 #2)              | 33.28 | 22.05 | −11.23 | **−34 %** |
| **autoferry_scenario3** (Cl-2 #2)              | 35.94 | 20.85 | −15.09 | **−42 %** |
| **autoferry_scenario4** (Cl-2 #2)              | 31.94 | 14.77 | −17.17 | **−54 %** |
| **autoferry_scenario5** (Cl-2 #3 UKF win)      | 33.49 | 20.88 | −12.61 | **−38 %** |
| **autoferry_scenario6** (Cl-2 #2)              | 30.55 | 18.87 | −11.68 | **−38 %** |
| **autoferry_scenario4_anchored**               | 2.64  | 1.50  |  −1.14 | −43 % |
| autoferry_scenario6_anchored                   | 5.60  | 5.11  |  −0.49 | −9 %  |
| philos                                         | 69.43 | 63.65 |  −5.78 | −8 %  |
| autoferry_scenario22                           | 36.87 | 42.29 |  +5.42 | +15 % |
| autoferry_scenario13                           | 21.49 | 42.08 | +20.59 | **+96 %** |
| autoferry_scenario16                           | 25.79 | 46.00 | +20.21 | **+78 %** |
| autoferry_scenario17                           | 25.20 | 44.84 | +19.64 | **+78 %** |
| dense_clutter                                  | 10.91 | 32.47 | +21.57 | **+198 %** |
| autoferry_scenario2_anchored                   | 2.34  | 6.84  |  +4.51 | +193 % |
| autoferry_scenario3_anchored                   | 1.54  | 4.60  |  +3.06 | +199 % |
| autoferry_scenario5_anchored                   | 3.06  | 6.88  |  +3.82 | +125 % |
| **autoferry_scenario13_anchored**              | 3.12  | 26.82 | +23.70 | **+759 %** |
| **autoferry_scenario16_anchored**              | 2.35  | 27.60 | +25.25 | **+1074 %** |
| **autoferry_scenario17_anchored**              | 2.63  | 23.12 | +20.49 | **+780 %** |
| **autoferry_scenario22_anchored**              | 3.42  | 17.75 | +14.33 | **+418 %** |
| crossing / overtaking / head_on / parallel_targets / ais_dropout / clock_skew / speed_change / crossing_dropout / crossing | (5–15) | +25–60 % each | +1–6 | small abs |
| non_cooperative                                | 19.85 | 19.85 |  0.00 | 0 % (bearing-only; PMBM births skipped by canInitiateTrack) |

### Pattern

1. **Structural win on the Cl-2 #2 over-confidence scenarios.**
   PMBM beats MHT by **34–54 %** on autoferry sc2/3/4/5/6
   unanchored — the exact scenarios where Cl-2 #2 manifests as
   "joint existence + association coupling at re-acquisition" that
   IPDA + TOMHT can't reach. The Cl-3 design hypothesis is
   validated: jointly Bayesian existence×association cleans up the
   re-acquisition phantom-confidence behaviour without any tuning.
   This closes Cl-2 #2 as a structural fix, conditional on the
   Phase 1.5 work below.

2. **ID flapping dominates everything else.** PMBM emits **100–170
   id_switches per scenario** on autoferry (vs MHT 0–50), and
   **20–60 per scenario on clean synthetics** (vs MHT 0). Every
   gated measurement births a fresh Bernoulli that the within-id
   Bernoulli merging step (§3.5 of pmbm-design.md, not yet
   implemented) is supposed to fold back. With measurement-driven
   birth running every scan, clutter returns mint new ids that
   live for several scans before pruning — this inflates OSPA /
   GOSPA cardinality penalty and is the dominant residual cost on
   every scenario other than the Cl-2 #2 winners. Phase 1.5 fix:
   §3.5 within-id merging + only birth PPP where no existing
   Bernoulli gates.

3. **Anchored variants regress 5–11×.** PMBM doesn't wire
   `SensorBiasEstimator` (the MHT canonical's bias correction
   path). On the anchored scenarios the MHT canonical applies a
   Schmidt-KF measurement correction that PMBM is missing — so
   PMBM is essentially measuring "PMBM without bias correction vs
   MHT with bias correction" on those rows, an unfair A/B.
   Phase 1.5 must wire the bias provider into the PMBM
   `processBatch` measurement-correction call site (same hook
   shape as MhtTracker::setSensorBiasProvider).

4. **dense_clutter +198 %** is the same id-flap problem, sharper:
   high clutter rate × measurement-driven-birth + no merging.

5. **philos lifetime 0.005**. Lifetime ratio drops from 0.31 (MHT)
   to 0.005 (PMBM) on the real-AIS philos scenario. Diagnosis
   pending — likely a sparse-AIS interaction with the measurement-
   driven birth rate. Treat as a Phase 1.5 investigation, not a
   structural blocker.

### Takeaway

PMBM Phase 1 ships the **structural** result the design predicted:
joint existence×association coupling fixes Cl-2 #2 cleanly (−34
to −54 % GOSPA on autoferry sc2–sc6 unanchored). Every other
regression is traceable to *implementation* gaps with named fixes
already in the design doc — they do not invalidate the Cl-3
direction, they define the Phase 1.5 work list. **Cl-3 stays the
endgame; the next milestone is Phase 1.5 (Bernoulli merging + smart
birth + bias-provider wiring), then a re-bench.**

### Phase 1.5 work list (in priority order)

1. **Smart birth + within-id Bernoulli merging (§3.5).** Highest
   expected payoff: kills id flapping on every scenario, brings
   anchored / clean / dense_clutter back into parity with MHT
   without touching the Cl-2 #2 wins.
2. **Wire `SensorBiasEstimator` into PMBM.** Same hook as MHT;
   bias correction is a per-measurement pre-pass that composes
   cleanly in front of the update.
3. **Investigate philos collapse.** Either tighten the measurement-
   driven-birth rate for sparse-rate scenarios, or look at AIS-
   only-source interaction with the existing-Bernoulli vs new-
   target competition.
4. After (1)–(3), re-bench against the same MHT canonical CSV. If
   the Cl-2 #2 wins survive and everything else returns to parity
   or better, Phase 1 is complete and Phase 2 (full
   IMM-per-Bernoulli mixture as the Bernoulli's spatial density,
   not just the inner estimator) becomes the next slab.

## 2026-06-20 (later) — [Cl-2 #2 (a)+(b) close-out] Lifecycle re-tune + init-cov widening rejected: cardinality bloat broadly regresses GOSPA

**Premise.** Cl-2 #2 left open in the north-star doc with two
candidate fixes inside the canonical IMM+MHT stack:
- (a) IPDA+VIMM lifecycle re-tune — looser demote, longer
  ever-confirmed memory (`ipda_persistence` 0.99 → 0.995,
  `ipda_delete_threshold` 0.05 → 0.02).
- (b) Track-spawn init-covariance widening
  (`kImmInitSpeedStd` 10 → 15, `kImmInitOmegaStd` 0.1 → 0.2).
Target: env-1 sc3 unanchored median NEES ≈ 15 (post-UKF
canonical) should fall toward 1.4. Mechanism intended: looser
lifecycle keeps tracks alive through brief misses → P grows by
accumulated Q → re-confirmation has honest uncertainty; wider
init-cov starts fresh tracks honest about velocity/turn rate.

**Method.** Edit `makeMhtConfig` and `kImmInit*` constants in
`core/benchmark/Config.cpp`. Add `imm_cv_ct_mht_oldlife`
ablation that reverts (a)+(b) for attribution. Full autoferry
slice (18 sc × 21 configs × seed 0). Pinned:
`docs/baselines/cl25_life_20260620.csv`.

### Result — broadly worse on real data

**Autoferry UNANCHORED (the target regime):**

| | mean Δ | median Δ | NEW worse | NEW better |
|---|---:|---:|---:|---:|
| GOSPA % | **+4.3** | +6.3 | **8/9** | 1/9 |
| RMSE %  | **+10.4** | +9.2 | 6/9 | 3/9 |
| NEES median | +0.36 | +0.07 | 5/9 | 4/9 |
| lifetime % | +1.9 | +1.6 | 1/9 | 8/9 |

**Autoferry ANCHORED:**

| | mean Δ | median Δ | NEW worse | NEW better |
|---|---:|---:|---:|---:|
| GOSPA % | **+17.1** | +13.6 | **8/9** | 1/9 |
| RMSE % | −0.2 | +0.01 | 6/9 | 3/9 |

Standout regressions: sc3_anchored GOSPA **+56%**, sc6_anchored
+28%, sc4_anchored +26%, sc6 unanchored RMSE +39%, sc13 RMSE
+25%. **sc3 unanchored NEES median 15.0 → 17.6 — the wrong
direction on the very scenario that motivated the work.**

### Mechanism — cardinality bloat, not localization

Anchored RMSE essentially flat (≤±3%) while anchored GOSPA
explodes +17% mean. RMSE measures *localization* on the
truth-matched tracks; GOSPA includes a *cardinality penalty*
for extra tracks. The combo of looser lifecycle (kept tentative
false tracks alive longer) and wider init cov (gates pulled
more measurements into more competing branches, sustaining
more false-positive hypotheses) bloated the hypothesis tree
without improving localization. Higher lifetime% (+1.9% on
unanchored) confirms tracks are persisting longer — real ones
and fake ones together.

### Why "honest uncertainty" didn't help NEES

The wider init-cov *did* widen P at spawn, but only briefly —
the filter's posterior shrinks rapidly under the first few
updates regardless of the prior. The persistent over-confidence
on re-confirmed tracks isn't fixable at *initialization* time;
it's about the *recovery* path after a brief miss. The lifecycle
change didn't address recovery directly either: it just made
the track survive longer in coast, but during coast the
estimator already adds Q correctly. The over-confidence comes
from somewhere else — likely the IPDA hit recursion treating
re-confirmation as if the gap never happened. Real fix here is
either deeper IPDA work or a JIPDA-class joint existence
recursion, which is **the Cl-1 sibling-pipeline experiment, not
a stackable change to Cl-2** (see §22 of
`docs/learning/22-tracker-stack-alternatives.md` — slice 5 is a
fork, not a stack).

### Decision

**Reverted both** (a) and (b). Inline comments in
`Config.cpp` document the bounds (init-cov widening direction
and lifecycle persistence direction) so a future drive-by
attempt sees the breadcrumb. `_oldlife` ablation dropped (no
longer needed for attribution).

`cl25_life_20260620.csv` kept as a negative-result baseline so
the cardinality-bloat mechanism is reproducible.

### Lesson

A standalone lifecycle/init-cov tweak cannot fix
re-confirmation over-confidence — the mechanism lives in the
joint existence + association coupling. Future Cl-2 #2 work
should attack that directly (more sophisticated IPDA recursion,
or treat it as the Cl-1 sibling experiment). Cl-2 #2 is now
**deferred indefinitely** in favour of going straight to Cl-3
(PMBM), which collapses slices 4-6 into one RFS recursion and
makes the question moot.

---

## 2026-06-20 — [Cl-2 #3 close-out] UKF inside IMM promoted to canonical inner filter; EKF preserved as `imm_cv_ct_mht_ekf` ablation

**Premise.** Cl-2 #3 in the north-star doc: build `ukf_cv_ct_mht`,
measure against the gated canonical, either ship UKF or formally
close the inner-filter question in EKF's favour. Implementation
landed as an `ImmEstimator` constructor flag (`use_ukf=true`)
dispatching per-mode sigma-point predict (propagate (2n+1) sigma
points through f, reconstruct mean/cov from weighted sums + Q)
and update (reconstruct (z̄, S, Pxz) from sigma-point
measurements, gain `K = Pxz S⁻¹`, posterior
`P − K S Kᵀ`). All other canonical wiring unchanged
(motion models, TPM, bias estimator, lifecycle).

**Bench.** `docs/baselines/cl23_ukf_full_20260619.csv` — 20
configs × 29 scenarios × seed 0 (autoferry 18, philos 1,
synthetic 10). UKF was config `imm_cv_ct_mht_ukf` for this
measurement; the deltas below are vs the EKF canonical
`imm_cv_ct_mht`. After promotion, the rows reverse roles: the
"EKF column" becomes `imm_cv_ct_mht_ekf` (preserved ablation)
and the "UKF column" becomes `imm_cv_ct_mht` (new canonical).

### Per-slice headlines

| slice | n | GOSPA mean Δ | UKF wins | verdict |
|---|---:|---:|---:|---|
| Autoferry unanchored (Cl-2 #2 regime) | 9 | **−12.3%** | **9/9** | dominant |
| Autoferry anchored | 9 | −0.4% | 4/9 | flat |
| Synthetic (linear-CV with clean noise) | 10 | **+5.7%** | 1/10 | regression |
| Philos (Boston-harbor replay) | 1 | −4.6% | 1/1 | win |
| **Overall (29 scenarios)** | 29 | **−2.1%** | 15/29 | mixed-but-positive |

**Standout autoferry-unanchored wins:** sc17 GOSPA −20.5% /
RMSE −30.7%; sc22 GOSPA **−21.7%** / NEES p95 **−4394** / p99
**−4558** (tail collapse fixed); sc3/4/6 all −14 to −16% GOSPA.
9/9 NEES median improvements. 9/9 `coverage_95` improvements.

**Synthetic regression mechanism (the catch).** Synthetic
generators use pure linear CV motion with clean Gaussian noise
— exactly the case where EKF is theoretically optimal. UKF's
sigma-point reconstruction adds tiny numerical noise but no
information. The real-data wins all come from the CT mode under
actual maneuvering, where EKF's linearization at the mode's
mixed-prior omega leaks information that UKF captures exactly
to second-order moments.

**Tail "regressions" on sc13/sc17 unanchored p99 (+1223 /
+711).** Same Cl-2 #1 metric-artefact pattern: `nees_median`
essentially unchanged (−0.03 / −2.74), `coverage_95` improved
(+0.01 / +0.06), only the extreme tail moves — same
Hungarian-ID-switch-boundary signature that drove the
sc13_anchored mean = 69 close-out. Not a UKF problem.

**Promotion decision: ship.** Real maritime data is what
deployment cares about. Autoferry unanchored is the exact
regime Cl-2 #2 left open; getting **9/9 GOSPA wins (mean
−12.3%)** is the result Cl-2 #2 was looking for. Synthetic
regressions are bounded (≤13%) and have a principled
explanation. Anchored stays flat (no regression risk).

### Changes shipped

- `core/estimation/ImmEstimator.{hpp,cpp}`: per-mode sigma-point
  predict + update behind `use_ukf` constructor flag (default
  false to preserve the explicit-EKF call sites in
  `_robust`/`_noisy`/etc; canonical factories pass true).
- `core/benchmark/Config.cpp`:
  - `makeImmCvCt` now passes `use_ukf=true` (CANONICAL).
  - `makeImmCvCtBearGuard`, `makeImmCvCtNoisy`,
    `makeImmCvCtRobust` switched to `use_ukf=true` for slice
    isolation — all "canonical + X" variants share inner-filter.
  - New `makeImmCvCtEkf` factory + `imm_cv_ct_mht_ekf` config
    pinning EKF (the pre-2026-06-20 canonical).
  - `imm_cv_ct_mht_ukf` config retired (redundant with
    canonical).
- `tests/benchmark/test_config.cpp`: pinned label set updated.
- `tests/estimation/test_imm_estimator.cpp`: new
  `UkfInnerFilterTracksAndShrinksLikeEkfOnLinearMeasurement`
  sanity check — Position2D update must agree to 1e-6.
- Bench pinned: `cl23_ukf_full_20260619.csv`. Label remap: rows
  labelled `imm_cv_ct_mht` are the OLD EKF canonical (=
  current `_ekf`); rows labelled `imm_cv_ct_mht_ukf` are the
  NEW canonical. Re-bench after promotion will normalise this.

**Cost summary across the 18 dependent ablations:** every
`makeImmCvCt`-derived config (nobias, novis, mofn, cmap, ipda,
recapture, jpda variants) automatically inherits UKF; we
expect their deltas to mirror canonical's autoferry-unanchored
wins. `_bearguard`, `_robust`, `_noisy` explicitly switched.

**Lessons for the next inner-filter experiment.** The slice
separation in §22 of `docs/learning/` is exactly what made this
clean: motion model unchanged, TPM unchanged, lifecycle
unchanged, bias unchanged — only the per-mode filter math
swapped. The diff to the bench was attributable. Apply this
template before any future Cl-2-class change.

---

## 2026-06-19 (later 5) — [Cl-2 #4 close-out] EO/IR R tightening rejected: bench measures catastrophic env-2 anchored regression; Step 2 NIS-based recommendation was misleading

**Premise.** Cl-2 #4 in the north-star doc: tighten env-2
`bearing_std_rad` from 0.0925 → ~0.06 per the Step 2 NIS finding
(gated canonical α̂ = 0.35/0.40 on EO/IR → "R conservatively
loose by 2.5-3×"). Predicted: "small NEES improvement on
anchored env-2; safe direction".

**Method.** Edit `adapters/benchmark/ReplayScenarioRun.cpp:248`
(0.0925 → 0.06 for env-2 urban scenarios only), full autoferry
slice on 6 IMM+MHT configs × 18 scenarios × seed 0. Pin:
`docs/baselines/cl24_tightR_20260619.csv`. Compare to the gated
canonical baseline `cl21_metrics_full_20260619.csv`.

**Result. Clear regression on the anchored runs the change was
supposed to help.** Δ vs cl21 baseline:

| sc (anchored) | GOSPA | RMSE | NEES med | NEES p95 |
|---|---:|---:|---:|---:|
| sc13_anchored | +1.5% | −8.1% | +0.14 | +1.70 |
| sc16_anchored | **+63.3%** | **+72.2%** | +0.35 | +25.53 |
| sc17_anchored | **+88.1%** | **+87.7%** | +0.30 | +1.08 |
| sc22_anchored | **+18.9%** | **+53.3%** | +0.24 | +13.28 |

Env-2 unanchored: RMSE also blew up (sc13 +245%, sc22 −33%); NEES
p99 went catastrophic (sc13 +112000, sc17 +17000). Env-1
bit-identical (we did not touch env-1 R) — verified zero delta
across all five scenarios × three configs.

**Mechanism.** The Step 2 NIS analysis read α̂ = innovation² /
(HPH^T + R) as "R is loose". On the **gated canonical** that was
the wrong read: the bias estimator removes systematic offset on
anchored runs, so innovations shrink — α̂ goes down even when R
matches the physical sensor noise. The *true* sensor noise floor
(≈ 0.088-0.095 rad empirically on env-2 EO/IR residuals before
debias) is what bounds how tight R can be. Forcing R below that
floor leaves the filter overconfident; the next outlier-class
measurement (urban shoreline / clutter) pulls state hard and
GOSPA + RMSE collapse.

**Decision: revert and close.** Keep env-2 `bearing_std_rad` at
0.0925. Inline comment in `ReplayScenarioRun.cpp:248` documents
the bound so a future drive-by tightening attempt sees the
breadcrumb.

**Lesson for Step 2-style analyses.** α̂ alone is not a
calibration target on a stack with online bias correction —
small α̂ can be "R is loose" or "innovations are small because
bias removed the systematic chunk". Distinguishing them needs
either (a) an explicit residual-σ measurement on the post-debias
stream, or (b) running α̂ alongside a `nobias` ablation. Item
filed for the next Step-2-style sweep.

**Bench cost.** 18090 rows × 1 seed × ~5 min on 19 configs.
`cl24_tightR_20260619.csv` kept as a negative-result baseline so
the bound is reproducible.

---

## 2026-06-19 (later 4) — [Step 5] SensorKind::Cooperative added as positional anchor alongside AIS

**Change.** New `SensorKind::Cooperative` enum variant (fleet
partner sharing its own platform GNSS). Wired as an additional
positional anchor:

- `core/types/Ids.hpp` — new enum variant + comment explaining
  identity-in-attributes invariant.
- `core/bias/SensorBiasPairExtractor.cpp:14` — `isAnchorKind` now
  returns true for `Ais || Cooperative`. Cross-sensor extractor
  treats either as a valid anchor for `pos`/`bearing`/`cross`
  pair extraction.
- `core/bias/AisArpaPairExtractor.cpp:11` — `isAisKind` now
  matches `Ais || Cooperative` (v1 heading-bias path).
- `core/benchmark/Sweep.cpp:48` — `sensorName` switch handles
  the new variant (label `"cooperative"`).
- `docs/sensors/sensor-reference.md` §4b — full reference entry.

**Framing.** This is additive, not a replacement for AIS. When
both AIS and Cooperative report on the same target in the same
cycle, both are valid anchors — selection between them per pair
is a future tuning knob, not a Step-5 concern.

**Tests.**
- `tests/bias/test_ais_arpa_pair_extractor.cpp` —
  `CooperativeGnssActsAsAnchorLikeAis` (1 new).
- `tests/bias/test_sensor_bias_estimator.cpp` —
  `EmitsPairFromCooperativeAndLidarContributions` (1 new).
- Full bias/pair/sweep gtest set: 77 tests pass (unchanged set
  + 2 new).
- Bench determinism: green.

**No bench delta** — no scenario currently emits Cooperative
measurements, so this is wiring-only. A synthetic
cooperative-vs-AIS-as-anchor sweep is filed as next-step work
(would test that bias convergence is identical when Cooperative
substitutes for AIS, and that two anchors of different kinds on
the same target both contribute).

**Decision.** Ship as canonical wiring; consumers can begin
producing Cooperative measurements without further engine
changes. No retune of any existing config.

---

## 2026-06-19 (later 3) — [Cl-2 #2 scoping] env-2 BOT / env-1 unanchored gap: no cheap canonical promotion; defer to longer-term work

**Premise.** Cl-2 #2 — sc5/sc6/sc22 env-2 BOT pathology — was framed
in the north-star doc as "the biggest remaining MHT-class gap to
Helgesen, ship `_bearguard` if clean else build modified-polar EKF".
With Cl-2 #1 closed as metric-artefact, re-measure the env-2 BOT
candidates against the gated canonical (post step 0) and decide.

**Pinned bench.** `docs/baselines/cl21_metrics_full_20260619.csv`
(9 configs × 18 autoferry scenarios × 1 seed, with the new
`nees_median` / `nees_p99` headline metrics).

### Bearguard re-measured against gated canonical

`_bearguard` ablation differs from gated canonical by **two** axes:
the LOS-clamp guard AND (incidentally) bias-estimator-off. To
isolate the guard's actual contribution, compare bearguard vs
`_nobias` (both bias-off; only the guard differs).

| sc (unanchored) | canon | nobias | bearguard | guard's lift |
|---|---:|---:|---:|---:|
| sc2  | 38.45 | 38.45 | 37.87 | −1.5% |
| sc3  | 43.93 | 43.93 | 43.09 | −1.9% |
| sc4  | 40.14 | 40.14 | 39.40 | −1.8% |
| sc5  | 36.67 | 36.67 | 36.45 | −0.6% |
| sc6  | 37.49 | 37.49 | 37.26 | −0.6% |
| sc13 | 23.54 | 23.54 | 22.21 | −5.7% |
| sc16 | 26.87 | 26.87 | 25.04 | −6.8% |
| sc17 | 31.97 | 31.97 | 30.54 | −4.5% |
| sc22 | 47.97 | 47.97 | 46.10 | −3.9% |

Anchored: bit-identical to `_nobias` on every scenario (the LOS
clamp doesn't fire when truth-AIS pins position).

**Read.** The guard delivers 0.6–6.8% GOSPA improvement on
unanchored, 0% on anchored. No regressions on NEES tails. **Real
but small.** Not transformative. *Could* promote to canonical for
the uniform unanchored gain, but the upside is bounded.

### Recapture re-measured

`_recapture` (adaptive recapture-gate, bias-off) shows headline
GOSPA wins of 10–36% on every autoferry unanchored scenario. But
the underlying mechanism is *wider gates allow stale tracks to
re-capture late-arriving measurements*, which trades **lifetime
ratio** for fewer ghost tracks:

| sc | canon gospa | recap gospa | canon life | recap life | canon p99 | recap p99 |
|---|---:|---:|---:|---:|---:|---:|
| sc3  | 43.93 | **28.28 (−36%)** | 0.88 | **0.66 (−22pp)** | 899 | 931 |
| sc17 | 31.97 | **25.48 (−20%)** | 0.90 | **0.39 (−51pp catastrophic)** | 590 | 286 |
| sc22 | 47.97 | **36.80 (−23%)** | 0.85 | **0.74 (−11pp)** | 10069 | **93036 (×9 worse)** |
| sc16 | 26.87 | 24.21 (−10%) | 0.85 | 0.78 (−7pp) | 339 | 2095 |
| sc4  | 40.14 | 31.96 (−20%) | 0.94 | 0.87 | 1033 | 1870 |

Operationally **not shippable as canonical.** Halving sc17 lifetime
to win 6 GOSPA points is a bad operational trade — we'd lose target
contact 60% of the time on that scenario. The p99 NEES tail also
explodes on sc22 (10k → 93k). GOSPA's cardinality cost is hiding
the real lifetime regression.

### Underlying mechanism (unanchored env-1)

Median NEES on the canonical (and `_nobias`) is now visible
post-Cl-2 #1: sc3 unanchored median = 20, sc5 = 11.7, sc6 = 9.4.
χ²₂ expected median ≈ 1.4. So the filter is **genuinely
over-confident by ~10×** on env-1 unanchored — not a metric
artefact. The 2026-06-13 reading still holds: "env 1 gap is
cardinality-driven — track breaks dominate the metric, and the
paper's VIMM-JIPDA recovers from misses on something the IMM-MHT
configuration we run does not."

The over-confidence mechanism: when a track is briefly missed and
re-confirmed (M-of-N or IPDA visibility re-fires), the new track
starts with a *prior covariance from init*, which is calibrated for
synthetic scenarios but too tight for autoferry maneuvering between
losses. The filter then under-reports its own uncertainty until
sustained tracking pulls it back.

### Cl-2 #2 close-out

- `_bearguard`: small uniform gain, no regression. *Defensible but
  not load-bearing*. Recommendation: don't promote unilaterally;
  fold in if/when a richer Cl-2 #2 fix lands and we re-baseline.
- `_recapture`: not shippable as canonical (lifetime cost too high
  on sc17 / sc3 / sc22). Keep as ablation; its GOSPA headline is
  useful for understanding GOSPA's cardinality bias, not for
  deployment.
- The honest Cl-2 #2 fix is **lifecycle / track-init covariance**
  work, not BOT-specific. Candidates:
  1. **Lifecycle re-tuning**: looser demote threshold, longer
     "ever-confirmed" memory, IPDA visibility-decay rate, etc.
     Small lift, possibly significant impact.
  2. **Track re-init covariance prior**: increase init covariance
     so re-confirmed tracks honestly report wider P. Trivial code
     change; measurable impact on NEES.
  3. **JIPDA-class lifecycle (sota-roadmap §2)**: the paper's
     actual fix. Multi-day; serves Cl-1's class-controlled
     extension as a side benefit.
- Defer (1)/(2) as the next round of Cl-2 #2 sub-tasks; (3) stays
  parked behind Cl-3 priorities.

### Implicit re-ordering

| Step | Status |
|---|---|
| Cl-2 #1 | closed 2026-06-19 (metric-artefact) |
| Cl-2 #2 | **partially scoped 2026-06-19**: `_bearguard` small, `_recapture` not shippable, real fix is lifecycle/init-cov work. Defer the algorithmic investigation. |
| Step 5 (Cooperative GNSS) | **NEXT** — small, additive deployment win |
| Cl-2 #3 (UKF inside IMM) | small, safe, measurable |
| Cl-2 #4 (EO/IR R tightening) | small, safe |
| Cl-2 #2 deeper (lifecycle / init-cov) | re-open after Step 5 / Cl-2 #3 |
| Cl-3 (PMBM) | the endgame, after the above stabilises |
| Cl-1 SJPDA/JIPDA | deferred unless class-controlled comparison wanted |

## 2026-06-19 (later 2) — [Cl-2 #1 close-out] sc13_anchored NEES "catastrophe" is a metric-reporting artefact; close as no filter bug; add nees_median + nees_p99

**The premise we were investigating.** Step 0 left sc13_anchored at
NEES mean = 69 on the canonical with no obvious mechanism — the
bias estimator's correction was applied (anchor pairs present), but
NEES stayed catastrophic while other anchored env-2 scenarios saw
modest gains (sc16/17/22). The 2026-06-16 entry hypothesised
"recent_contributions reset on every ID switch", which on re-reading
the code today is **wrong** — `recent_contributions` is keyed by
`externalId()` and pruned only by time window
(`core/pipeline/MhtTracker.cpp:618`); metric-side ID switches do not
touch it.

**What's actually happening.** The bench harness emits only
`nees_mean` as the headline. Adding `nees_median` and `nees_p99` to
the NeesStats output (this commit) and re-bencing canonical-family
configs on sc13_anchored reveals:

| Config | mean | **median** | p95 | **p99** | cov95 |
|---|---:|---:|---:|---:|---:|
| `imm_cv_ct_mht`           | **69.07** | **0.37** | 7.71 | **1637** | 0.943 |
| `imm_cv_ct_mht_nobias`    | 24.27     | 0.44     | 6.83 | **873**  | 0.938 |
| `imm_cv_ct_mht_robust`    | 32.10     | 0.42     | 6.07 | 845      | 0.949 |
| `imm_cv_ct_mht_bearguard` | 24.27     | 0.44     | 6.83 | 871      | 0.938 |
| `imm_cv_ct_mht_ipda`      | 24.27     | 0.44     | 6.83 | 873      | 0.938 |
| `imm_cv_ct_mht_cmap`      | 24.96     | 0.44     | 6.78 | 873      | 0.940 |
| `imm_cv_ct_mht_mofn`      | 36.38     | 0.51     | 7.47 | 1067     | 0.934 |
| `imm_cv_ct_mht_recapture` | 24.27     | 0.44     | 6.83 | 873      | 0.938 |

**Read.** The filter is *fine* on sc13_anchored in every config:
median NEES ≈ 0.4 (well below the χ²₂ expected mean of 2), p95 ≈ 7
(at the χ²₂ 95% threshold of 6), cov95 ≈ 0.94 (right at the
expected 0.95). The headline NEES = 69 is **entirely tail-driven**:
nees_p99 reaches 873–1637 on every config, meaning ~1% of samples
have NEES values in the 1000s. Those extreme samples appear at
*metric-side ID switch reassignment events* — the truth-to-track
assignment greedy-matches under `assignPerStep` (with optimal
2026-06-18 Hungarian), and when truth_i flips from track_A to
track_B at scan k+1, track_B's posterior is briefly far from truth_i
(it was just tracking truth_j) → one or two extreme NEES samples
until the filter catches up or the next switch happens.

This pattern is **scenario-bound** (sc13 has 14 metric ID switches
between two close-spaced targets), not config-bound. Removing the
bias estimator (`_nobias`) drops mean from 69 → 24 because it
prevents ~9 of those switches; it does **not** improve median, p95,
or cov95.

**Confirming pattern across the matrix.** Tail-drag (= mean − p95)
shows two distinct regimes:

| Pattern | Scenarios | Read |
|---|---|---|
| **mean ≫ p95** — tail-dragged | sc13_anchored (61), sc17 unanchored (69) | Filter is fine; metric reassignment spikes drag mean. |
| **mean ≤ p95** — broadly distributed | every other autoferry scenario, both anchored and unanchored | If mean is high, filter is genuinely off — the headline is honest. |

The first regime is what was confusing us about sc13_anchored. The
second covers the rest of the matrix, including the genuine env-2
BOT pathology (sc5/sc6/sc22 unanchored, sustained high mean *and*
high p95).

### Code change

`core/benchmark/Consistency.{hpp,cpp}`: NeesStats gains `median` and
`p99` fields, computed via the existing `percentile` helper.
`Sweep.cpp` emits two new rows per scenario (`nees_median`,
`nees_p99`). `tests/benchmark/test_sweep.cpp` row-count pin updated
(30 → 32, NEES per-seed 6 → 8). 679 tests green.

### What this means for Cl-2 #1

The catastrophe was the reporting, not the filter. Cl-2 #1 **closes
as no filter bug**; the headline NEES on sc13_anchored is now
honest (`p95 = 7.71`, `median = 0.37` for canonical). The 2026-06-16
"recent_contributions reset on ID switch" hypothesis is retracted;
the code never did that.

### Eval-log convention going forward

Headline NEES for *any* scenario reads `(median, p95, cov95)` first.
`nees_mean` is reported but with a footnote when `mean / p95 > 2.0`
(the tail-dragged regime). This keeps the metric honest without
losing the mean for historical comparability. `comparison-baselines.md`
updated to drop sc13_anchored from the Cl-2 #1 open-work table; Cl-2
moves directly to env-2 BOT (sc5/sc6/sc22).

Pinned bench: `docs/baselines/cl21_metrics_full_20260619.csv`
(regenerating; new NeesStats fields).



**Premise.** Plan step 2: re-measure per-sensor NIS now that the bias
estimator's publish is gated. The standing claim from 2026-06-15
("radar trace_ratio = 4.02 → Q is 50× too large") predates Schmidt-KF
canonical promotion, the 2026-06-18 Hungarian metric, and the
2026-06-19 anchor-gating. Need fresh numbers before step 3 (SJPDA)
or any Q tuning.

**Method.** No new bench needed — `step0_gated_20260619.csv`
(canonical-gated, all 9 autoferry × 2 anchor variants × seed 0)
emits `nis_alpha_hat:<source>` and `nis_trace_ratio:<source>` per
update. α̂ = ε̄_NIS / dim → target 1.0; trace_ratio > 1 flags the
state-driven regime where α̂ is unreliable as an R-calibration
diagnostic.

### Aggregate by sensor (autoferry × {anchored, unanchored})

| sensor | α̂ median | α̂ range | trace_ratio median | rows tr>1 |
|---|---:|---|---:|---:|
| AIS (truth-anchor) | 0.08 | [0.03, 0.14] | 0.08 | 0/9 |
| radar | 0.88 | [0.35, 1.88] | 0.79 | **8/18** |
| lidar | 0.55 | [0.11, 1.05] | 0.21 | 1/18 |
| EO | 0.35 | [0.15, 0.74] | 0.09 | 0/18 |
| IR | 0.40 | [0.09, 0.81] | 0.08 | 0/18 |

### Reads

**The 2026-06-15 "Q too large" claim doesn't replicate.** Radar
trace_ratio sits at 0.04–5.66 (median 0.79) — eight scenarios
above 1, ten below. The 4.02 figure was a single-scenario
snapshot under stale state (pre-Schmidt-KF, pre-Hungarian, pre-
bias-canonical). Even on the rows where trace_ratio > 1 today, α̂
is in [1.15, 1.88] — that's not the "Q is 50× too large" regime,
it's "state covariance is comparable to R, α̂ unreliable here".
And — independently — eval-log 2026-06-16 already established that
tightening Q would shrink P and make NEES *worse* (item 12(c)
closed "Q is not the lever"). Treat the stale claim as retired;
no Q change.

**R is conservatively loose on EO/IR (~2.5–3×) and lidar (~1.8×).**
α̂ medians 0.35 (EO) / 0.40 (IR) / 0.55 (lidar), all in the
state-cov-doesn't-dominate regime (trace_ratio ≪ 1, reliable).
Configured σ values are 5.3° bearing (env-2 override, ~3-4°
empirical) and 3 m lidar (env-2 override, ~1.5 m empirical).
**Direction is safe** — over-conservative R never produces an
overconfident filter — but tightening to empirical would help
NEES marginally on the anchored scenarios. **Not blocking for
step 3.** Candidate change: env-2 EO/IR `bearing_std_rad` 0.0925
→ 0.06; lidar `lidar_pos_std_m` 3.0 → 2.0. Measure before
shipping; small impact expected given state already dominates
under the truth anchor.

**AIS truth-anchor α̂ ≈ 0.05 is a fixture artefact, not a
finding.** Truth-AIS injects truth as the measurement (σ = 5 m);
the post-update state matches truth almost exactly, so the next
AIS innovation is near-zero by construction. α̂ → 0 in this
limit. Real AIS in deployment would have non-zero target motion
between updates and this artefact wouldn't appear.

**Gating is calibration-neutral on unanchored runs (verified).**
On every unanchored autoferry scenario, NIS per-sensor is
**bit-identical** between `imm_cv_ct_mht` (gated canonical) and
`imm_cv_ct_mht_nobias` (no bias estimator): sc2 lidar 0.89 vs
0.89, sc2 radar 1.56 vs 1.56, sc2 EO 0.46 vs 0.46. This is the
expected outcome of the 2026-06-19 gating change — bias is
prevented from publishing without anchor data, so the Schmidt-KF
correction path never fires and R is never inflated. Empirical
proof the gate works as designed.

### Step 2 verdict: nothing blocks step 3

- No Q tuning (the 2026-06-15 motivation is stale).
- EO/IR/lidar R tightening is a small backlog item, not blocking.
- The gating produces honest NIS, including by leaving unanchored
  runs untouched.
- Per-sensor data committed alongside step 1's
  `step0_gated_20260619.csv`. Step 3 (SJPDA on the JPDA path)
  proceeds next.

## 2026-06-19 — [Cl-2 canonical fix] Step 0: canonical's bias estimator regresses NEES on unanchored urban scenarios; fix = anchor-gated publish

**Premise** (from prior session). When asked "what to do before JIPDA",
synthesized a plan from the log. Pushed back; re-verified against
code + fresh bench; three of six recommendations were obsolete or
contradicted by data already in the committed CSVs. The remaining
load-bearing claim was: on AutoFerry sc13_anchored, canonical NEES
= 73 while every MHT ablation (`_ipda`, `_recapture`, `_bearguard`)
sat at ~25. The two things the canonical does that the ablations
don't are wire the bias estimator and turn `use_visibility` on.
Step 0 was a clean 2-axis disambiguation.

### Ablations added

`imm_cv_ct_mht_nobias` (canonical minus the bias estimator,
visibility ON) and `imm_cv_ct_mht_novis` (canonical minus VIMM
visibility, bias estimator ON). Together with the existing
`_ipda` (both off, = `_nobias_novis`), the 2×2 separates the two
canonical choices on every autoferry scenario. `defaultConfigs()`
now returns 19; `tests/benchmark/test_config.cpp` pins the count
and the two labels.

### Bench (`step0_ablation` — 9 MHT configs × 9 autoferry × 2 anchor variants, seed 0)

NEES on canonical vs canonical-minus-one-axis. Visibility is
neutral to 4 decimals on every anchored row and within rounding on
every unanchored row. The bias-estimator wiring is the asymmetry:

| sc (unanchored) | canonical | `_nobias` | `_novis` | `_ipda` |
|---|---:|---:|---:|---:|
| **sc2**  | **1210** | 45 | 1222 | 46 |
| sc3  |   82 | 82 |  82 | 82 |
| sc4  |   70 | 70 |  65 | 65 |
| sc5  |   49 | 49 |  50 | 50 |
| sc6  |  122 | 121 | 131 | 131 |
| **sc13** | **57** | **7.7** | 58 | 7.7 |
| sc16 |   20 | 17 |  20 | 17 |
| sc17 |  265 | 265 | 265 | 265 |
| **sc22** | **1285** | **542** | 1314 | 584 |

Anchored variants are mixed but never as catastrophic: canonical
beats `_nobias` modestly on sc3/sc16/sc17/sc22; `_nobias` beats
canonical modestly on sc4/sc5; on sc13_anchored canonical is **69**
vs `_nobias` **24** (the original headline). GOSPA shifts are 4-4-1
across anchored, near-flat on unanchored — the bias estimator's
unanchored regression is a NEES catastrophe with negligible GOSPA
signature, which is why the symmetric-fusion invariance argument
from 2026-06-17 (item 13) had read it as "bit-neutral."

### Mechanism

`extractCrossSensorPositionPairs` walks pairs of non-AIS
positional contributions and lets the estimator's zero-mean prior
split any relative offset symmetrically across keys. The
**estimate** is GOSPA-invariant (the antisymmetric split cancels
in symmetric weighted fusion — verified 2026-06-17). The
**Schmidt-KF correction** is not: `R_eff = R + P_b` happens on
every consuming filter regardless of whether the prior allocation
is right. On sc2/sc13/sc22 unanchored — symmetric sensors, no
AIS, no offline calibration — the split is purely a guess; the
shifted measurements pull state off truth by O(δ/2) while the
filter's claimed covariance inflates, so NIS stays calibrated but
NEES diverges (truth vs estimate offset, not innovation magnitude).

### Fix shipped: anchor-gated publish

`PositionBiasPairObservation` and `BearingBiasPairObservation`
gain `is_anchor_source` (default `true`, preserving the AIS-
anchored callers). `SensorBiasEstimator::PositionState` and
`BearingState` track `anchor_obs_count`, incremented only when
the accepted observation's `is_anchor_source == true`.
`positionBias()` / `bearingBias()` gate `is_published` on
`anchor_obs_count > 0` in addition to the existing convergence
threshold. `extractCrossSensorPositionPairs` inherits anchor
status from its partner: if the anchor partner's bias is already
published (seeded with `treat_as_anchored=true`, or refined via
AIS), the pair counts as anchored; otherwise not. Seed APIs
(`setKnownPositionBias`, `setKnownBearingBias`) get a
`treat_as_anchored = false` default — the seed alone is the
operator's hypothesis, not an anchor; observations validate it.

Two tests updated: `SetKnownPositionBiasTightPriorPublishes`
became `…DoesNotPublishByDefault` + a paired `…AnchoredPriorPublishes`;
`CrossSensorRecoversBiasWithPinnedAnchor` now seeds the radar
side with `treat_as_anchored=true` (the test's intent — operator
asserts "this sensor is calibrated"). Full 679-test suite green.

### Measured deltas — canonical, before vs after gating

NEES, before → after on `imm_cv_ct_mht`:

| sc | unanchored | anchored |
|---|---|---|
| sc2  | **1210 → 45** (−96%) | 2.33 → 2.33 |
| sc3  | 82 → 82 | 0.90 → 0.90 |
| sc4  | 70 → 70 | 3.70 → 3.70 |
| sc5  | 49 → 49 | 4.02 → 4.02 |
| sc6  | 121 → 121 | 4.71 → 4.71 |
| **sc13** | **57 → 7.7** (−87%) | 69.07 → 69.07 (unchanged) |
| sc16 | 20 → 17 (−14%) | 2.71 → 2.70 |
| sc17 | 265 → 265 | 1.28 → 1.29 |
| **sc22** | **1285 → 542** (−58%) | 1.11 → 1.11 |

GOSPA shifts ≤ 1% across the board, both directions. Three
catastrophes removed; the modest anchored-env-2 wins from the
seeded-and-published path are preserved because anchor data is
present and the gate opens normally. No regression on the synthetic
suite. Bench: `step0_gated_20260619.csv` (regenerate on-host;
intermediate run not committed).

### Still open: sc13_anchored NEES = 69

Anchor data is present on sc13_anchored, so the gate opens
immediately on the first AIS-bearing pair — `_nobias` and
canonical-after-gating diverge by 45 NEES. The mechanism is
downstream of the publish gate: sc13_anchored has 14 ID
switches, each resets `recent_contributions` on the affected
track, so the AIS-bearing pair stream is sample-biased toward
the better-tracked target; the published bearing correction is
then systematically wrong on the swap-prone target. The right
fix is upstream coalescence/swap handling (SJPDA, step 3 in the
plan), not another bias-estimator tweak.

### Implication for `_bearguard` promotion

Pre-step-0, bearguard's sc13_anchored NEES 73 → 25 looked like
the "range-collapse guard works" story. With step 0 it's clear
the 73 was the bias-estimator regression and bearguard's drop is
mostly inherited from its `_nobias`-like default (the bearguard
ablation doesn't wire the bias estimator). On the gated canonical,
re-measure bearguard before deciding promotion — the headline
motivation just evaporated.

### Note for fleet-GNSS cooperative deployments (step 5)

The gating creates a clean deployment story for cooperative
fleet GNSS as an additional anchor source (alongside AIS, not in
place of it): emit those as a new
`SensorKind::Cooperative` Position2D source, extend
`SensorBiasPairExtractor::isAnchorKind` to recognise it, and
the existing extractors + the new gate compose correctly
(cross-sensor pairs inherit anchor status from the cooperative
partner; bias estimator publishes; Schmidt-KF correction flows).
This is the "no AIS, real anchor" regime the 2026-06-15 item-9
caveat called out and item 13 didn't quite reach.

### Baseline-comparison caveat (2026-06-18 Hungarian)

The before-and-after numbers in this entry are both on the
optimal-assignment metric introduced 2026-06-18. Do not cross-
compare to the 2026-06-17 `bench_xsensor` headline NEES values
(sc2 ≈ 56 in that CSV, ≈ 1210 here on a fresh build) — both the
build-reproducibility caveat from that entry and the metric
change apply. The 2026-06-19 deltas above are internally
consistent (same harness, same build, same metric, only the
bias-publish-gating differs).

## 2026-06-18 — Review #17: metric assignment greedy → optimal (Hungarian). Intentional re-baseline.

**Change.** `ospaGreedy`, `gospaGreedy`, and `assignPerStep` (the shared
truth↔track assignment feeding OSPA, GOSPA, id_switches, continuity, and
per-track RMSE/NEES) switched from greedy nearest-neighbour to optimal
min-cost assignment via `hungarianAssignment`. Function names retained for
call-site stability. OSPA: clipped-distance² cost matrix. GOSPA: augmented
(|X|+|Y|)² matrix with per-target miss/false dummy slots so a pair is matched
only when `d^p < 2·c^p/α`. `assignPerStep`: gated truth×track matrix.

**Why.** Greedy can lock a locally-cheap pairing that forces a globally-worse
remainder. In close-crossing geometry this both *manufactures* spurious
id_switches/OSPA spikes and *masks* real ID swaps (by keeping a stale
pairing) — both confound the A/B estimator comparisons this log exists to
make. Optimal assignment is the metric the OSPA/GOSPA definitions actually
specify (min over assignments).

**Measured impact (synthetic sweep, 17 configs × 10 scenarios × 5 seeds,
28166 rows).** 226 rows differ (~0.8 %), exclusively in head-on crossing
scenarios, and only on assignment-dependent metrics (ospa_mean, gospa_mean,
gospa_rms, id_switches, pos/sog/cog_rmse, nees). `id_switches` moves **both**
directions: e.g. `ukf_ct_gnn / head_on` 2→0 (greedy over-counted churn),
`imm_cv_ct_mht / head_on` 0→2 (greedy masked a real swap). Non-crossing
scenarios and all cardinality-only cases are unchanged. Unit-level: all
existing OSPA/GOSPA/assignPerStep tests still pass (greedy == optimal on
their simple geometries); two new tests (`Ospa/Gospa.UsesOptimalAssignmentNotGreedy`)
pin a collinear case where they diverge.

**Baseline hygiene.** This is a deliberate metric-definition change, so it is
*not* bench-neutral and historical `docs/baselines/*.csv` snapshots predate
it. Do **not** cross-compare id_switches/OSPA/NEES across the #17 boundary;
regenerate a fresh reference on-host when an exact comparison is needed.

## 2026-06-17 (later) — Item 13 cross-sensor anchored bias: shipped, fires correctly, AutoFerry-invariant due to symmetric fusion

Backlog item 13. Adds `extractCrossSensorPositionPairs` to
`SensorBiasPairExtractor`: for tracks passing eligibility
(`existence ≥ 0.95`, position-cov-trace `≤ 25 m²`) that have **no
AIS contribution** in the cycle window, emit one `(X, Y)` and one
`(Y, X)` position-bias-pair observation per ordered pair of distinct
`SensorBiasKey`s. Schmidt-KF folds the anchor side: subtract `b̂_Y`
from `z_Y`, add `P_b_Y` to `R_anchor`. Wired into the canonical's
PostScanHook after the AIS-anchored extractors. Unit tests + bench
determinism green; full sweep matches `bench_xsensor_20260617T183817Z.csv`.

### Acceptance criteria results

| # | Criterion | Result |
|---|---|---|
| 1 | Bit-identical on AIS-bearing tracks | ✅ all 9 anchored autoferry rows match canonical to 5 decimals |
| 2 | Estimator recovers true bias under pinned anchor | ✅ `CrossSensorRecoversBiasWithPinnedAnchor` test: lidar (3.0, −2.0) recovered to within 0.6 m after 60 cycles with radar pinned to zero |
| 3 | Bench determinism preserved | ✅ `BenchDeterminism.RepeatedSweepProducesIdenticalRows` green |
| 4 | AutoFerry env-1 raw GOSPA −5..−15% | ❌ **zero delta** (37.5..43.9 m unchanged) |

### Diagnostic — extractor is firing, just not biting

A debug-instrumented run of `imm_cv_ct_mht` × `autoferry_scenario2`
(seed 0) confirms the extractor produces and the estimator accepts:

```
[bias-debug] imm_cv_ct_mht | autoferry_scenario2 seed=0
  ais_pairs=0 cross_pairs=980 accepted=852
  [lidar/autoferry_lidar] b=(+0.570, +0.081) trP=0.499 pub=1
  [radar/autoferry_radar] b=(-0.570, -0.081) trP=0.499 pub=1
```

Note the perfectly antisymmetric `(b̂_lidar, b̂_radar) = (+δ/2, −δ/2)`
with `δ ≈ 1.14 m east`. The cross-sensor coordinate descent caught the
relative offset; the zero-mean prior allocated it symmetrically.

For comparison the *anchored* `sc2_anchored` run (truth-AIS injected)
recovers absolute biases:

```
  [lidar/autoferry_lidar] b=(+0.971, +0.181) trP=0.047 pub=1
  [radar/autoferry_radar] b=(-0.232, +0.090) trP=0.076 pub=1
```

Lidar carries most of the true bias; radar is nearly clean. The
cross-sensor pair difference `1.20 m east` matches the AIS-anchored
`b_lidar − b_radar ≈ 1.20 m east` — same relative answer, but split
differently across the two sensors.

### Why the corrections cancel — symmetric-fusion invariance

For a symmetric weighted-mean fusion (lidar 3 m σ, radar 5 m σ — close
enough), the cross-sensor split is a no-op in the output:

```
fused = w_X · (z_X − b̂_X) + w_Y · (z_Y − b̂_Y)
      = w_X z_X + w_Y z_Y − (w_X − w_Y) · δ/2
      ≈ uncorrected_fused − O(0.1 m)   when w_X ≈ w_Y
```

A 0.1 m shift is far below the steady-state `pos_rmse_m ≈ 17 m` and
the `GOSPA c = 20 m` cutoff. Result: gospa_rms / id_switches /
pos_rmse / nees_mean all bit-identical.

Three regimes break the symmetry and would unlock measurable benefit;
see `sensor-bias.md §Symmetric-fusion invariance` for the full
discussion:

1. **Intermittent AIS coverage.** Once a track has an AIS-bearing
   segment, that segment converges absolute biases; subsequent
   AIS-less segments anchor the asymmetry through the Schmidt fold.
2. **Asymmetric sensor variance** (one `R` much tighter than the
   other).
3. **Pre-seeded per-sensor priors** via `setKnownPositionBias`
   (mirrors the env-2 EO/IR bearing-bias seed pattern from item 9).

For AutoFerry env-1 raw — symmetric sensors, no AIS, no offline
calibration — none of (1)/(2)/(3) is active. Item 13's math is sound
and the path is correct; the empirical delta is zero on this dataset
because the symmetric prior allocation cancels in the fusion operator.

### Where this leaves us

- **Item 13 closed.** Math correct, fires correctly, deployment fit
  is the **pinned-anchor path** (operator pre-seeds one sensor's
  bias from factory calibration documentation, the other learns
  against it). This is the spec's option (a) — bootstrap — and it
  works as designed per the unit tests.
- **The spec's 5-15% AutoFerry gospa target was over-optimistic**
  for the symmetric-sensor / no-anchor case. Reported honestly here;
  no eval-log re-write needed for the 2026-06-15 item-9 anchored
  measurement (that finding stands — bias estimator on top of AIS
  gave a ~5% env-1 reduction; cross-sensor without AIS gives zero
  because the prior makes the split symmetric, which fusion cancels).
- **Next.** SOTA roadmap §5 finish (VB-adaptive Student-t) is now
  the cleanest open frontier — it directly addresses the EO/IR
  clutter regime that real-data measurements pin as the dominant
  error source.
- **Latent value.** When backlog item 14 (sensor-reported per-
  measurement R) lands and produces asymmetric variance, item 13
  may start to bite without further code changes — leave it on by
  default.

Pinned baseline: `docs/baselines/bench_xsensor_20260617T183817Z.csv`
(17 configs × 29 scenarios × 10 seeds = 2 023 runs, 47 min).
Synthetic suite bit-identical to canonical to all 5 decimals; all
autoferry rows bit-identical or within 1 m (sc22 / sc4 anchored
minor rounding shifts at the 1e-3 level from `cross_pairs=0` →
post-scan-hook empty-vector early-out path differing from
canonical's hook semantics).

## 2026-06-17 — Item 9 closed: bias-estimator wiring promoted to canonical, env-2 seed hook landed

Item 9 close-out. Three things shipped at once:

1. **`imm_cv_ct_mht` now wires `SensorBiasEstimator` unconditionally.**
   `Config::build_sensor_bias_estimator` is non-null on the canonical;
   `Sweep::runSweep` constructs the estimator, calls
   `tracker.setSensorBiasProvider(...)`, and installs a `PostScanHook`
   that calls `predictTo(scan_t)` + `extractPairs(...)` after each
   scan. On scenarios with no anchor source (every synthetic) the
   estimator stays at its zero prior and never publishes — the
   bias-correction call site returns measurements unchanged. Result:
   **bit-identical to the legacy null-provider path on all 14
   synthetic scenarios** (head_on/crossing/overtaking/parallel_targets/
   dense_clutter/clock_skew/speed_change/non_cooperative/ais_dropout/
   crossing_dropout/scenario/philos — every per-seed gospa_rms matches
   the prior `bench_schmidt_20260616T105707Z.csv` to all five decimals).

2. **`imm_cv_ct_mht_biascal` retired** — it was bit-identical to the
   canonical on every scenario from the moment biascal-wiring became
   the canonical path. `defaultConfigs()` now returns 17 configs
   instead of 18; `tests/benchmark/test_config.cpp` pins the new
   count and asserts `configs.front().build_sensor_bias_estimator !=
   nullptr` so the canonical promotion can't silently regress.

3. **Per-scenario seed hook (`ScenarioRun::seedSensorBiasEstimator`).**
   Default is no-op. `AutoferryScenarioRun` overrides it for the four
   urban env-2 scenarios (sc13/16/17/22) to inject the offline-
   calibrated EO/IR bearing prior from
   `tools/autoferry_r_calibration.py`:
   - `autoferry_eo` bias = 7.0° (0.122 rad), σ = 0.3°
   - `autoferry_ir` bias = 4.9° (0.085 rad), σ = 0.3°

   σ = 0.3° equals `kBearingPublishSigmaRad` so the seed publishes
   immediately and online observations refine it. Env-1 scenarios
   deliberately do **not** seed — their bias is small (3–4°), the
   online AIS-anchored path catches it without help, and a wrong-env
   seed would distort the first few hundred observations.

### Measured outcome on autoferry (canonical, seed 0)

Baseline: `docs/baselines/bench_canonical_20260616T170135Z.csv` (17
configs × 29 scenarios × 10 seeds = 2 023 runs, 47 min wall on the
benchhost).

| scenario | env | gospa_rms vs schmidt | gospa_rms anchored |
|---|---|---|---|
| sc2  | 1 | 38.45 = 38.45 | 3.46 ≈ 3.46 |
| sc3  | 1 | 43.93 = 43.93 | 2.83 → 1.73 (**−39%**) |
| sc4  | 1 | 40.16 = 40.16 | 2.88 → 4.55 (+58%) |
| sc5  | 1 | 36.67 = 36.67 | 3.83 → 4.53 (+18%) |
| sc6  | 1 | 37.49 = 37.49 | 9.82 → 8.70 (−11%) |
| sc13 | 2 | 23.54 = 23.54 | 4.46 → 5.85 (+31%) |
| sc16 | 2 | 26.87 ≈ 26.87 | 4.01 → 4.40 (+10%) |
| sc17 | 2 | 32.01 = 32.01 | 5.27 → 4.50 (**−15%**) |
| sc22 | 2 | 47.98 → 47.48 (−1%) | 6.77 → 6.21 (−9%) |

**Honest reading:**

- **Unanchored urban runs are bit-identical** to the no-seed baseline
  on sc13/sc17 and within rounding on sc16, with sc22 the only
  noticeable shift (−0.5 m). The seed publishes but the
  bearing-bias correction has near-zero impact on
  data-association/tracker output on these fixtures — bearings still
  fail track initiation (`canInitiateTrack` is false for Bearing2D),
  and the radar+lidar position path that does initiate tracks isn't
  what the bearing seed targets. **The seed earns its keep on
  anchored env-2 (sc17 −15%, sc22 −9%); env-1 results are mixed
  (sc3 −39%, sc4/5 +18 to +58%)** — the per-scenario refinement the
  comment hints at is plausibly the right next step for env-1.
- **The MHT canonical's headline real-world story is unchanged**:
  raw urban env-2 gospa is 24–48 m, anchored is 4–6 m. The 2026-06-15
  truth-anchor finding is the load-bearing one; item 9's incremental
  contribution on top is at most modest, sometimes mildly negative
  on env-1.
- **No regression on the synthetic suite.** The full 624-test gtest
  binary passes (617 pass, 7 skipped for missing-fixture / replay
  guards), determinism test green.

### Where this leaves item 9

- **Closed.** The full v0.3.0 / v0.4.0 / v0.5.0 + Schmidt-KF cov fold
  (commit b1a15a3) + bearing-pair extraction (commit 970be0f) +
  per-target diagnostic tooling (commit e6a498f) + canonical
  promotion + env-2 seed pipeline is in place and pinned by tests.
- **Backlog children worth opening before declaring item 9 done-done:**
  per-scenario env-1 seed refinement (sc4/sc5 anchored regression
  suggests the env-1-zero assumption isn't quite right either);
  promoting the online bearing-pair path on env-1 anchored data to
  recover the schmidt-baseline anchored sc4 number.
- **Item 9 is no longer the binding constraint.** Next: item 12(c)
  Q-PSD calibration — the per-sensor NIS data from commit f2c357a
  (radar trace_ratio 4.02, α̂_radar = 2.17) points at Q being too
  large for the AutoFerry maneuvering envelope.

## 2026-06-15 (later) — Item 9 options 1 + 2 measured — match paper env 1, beat paper env 2 with the truth anchor

Following up on the morning's "anchor-starved" finding: options 1
(`AutoferryLoadOptions::inject_truth_anchor` → Position2D AIS
measurements at every truth sample, σ = 5 m) and 2 (project
RangeBearing2D into ENU when populating `SourceTouch`) shipped.
Bench run `docs/baselines/biascal_anchored_20260615T184047Z.csv`.

### Headline — env-level GOSPA RMS vs Helgesen 2022

| Env | Paper | navtracker canonical (no AIS) | navtracker canonical (truth-AIS) | navtracker biascal (truth-AIS) |
|---|---:|---:|---:|---:|
| 1 (open water)    | **20.37** | 43.4 | 20.6 | **19.6** |
| 2 (urban channel) | **30.97** | 33.9 |  7.1 | **7.2**  |

Two distinct effects show up in the data:

**(A) Truth-as-AIS injection dominates.** The single largest mover is
just having a Position2D AIS-class measurement in the fusion mix at
all. canonical: 43.4 → 20.6 (env 1), 33.9 → 7.1 (env 2). This is
the tracker doing what trackers do — fusing a higher-quality
positional sensor sharpens every track. It is **not** the bias
estimator working. It is what would also happen if the user
deployed with real Class-A AIS on a cooperative target.

**(B) Bias estimator's pure contribution on top of the AIS feed.**
Apples-to-apples comparison, both configs sharing the same AIS
stream:

| Env | canonical+AIS | biascal+AIS | Δ |
|---|---:|---:|---:|
| 1 (open water) | 20.57 | 19.63 | **−4.6%** |
| 2 (urban)      |  7.13 |  7.16 |  +0.4% |

Env 1 sees a real but modest reduction from running the bias
estimator on top of the AIS anchor. Env 2 sees essentially nothing —
the urban-channel scenarios have shorter target dwell, tighter
geometry, and a much smaller residual offset for the estimator to
catch.

### Per-scenario posRMSE (m) — the anchor cuts these by an order of magnitude

| Sc | env | canonical (no AIS) | canonical (truth-AIS) | biascal (truth-AIS) |
|---|---|---:|---:|---:|
| 2  | 1 |  8.6 | 2.00 | 1.88 |
| 3  | 1 | 25.7 | 1.79 | 1.49 |
| 4  | 1 | 11.4 | 1.46 | 1.39 |
| 5  | 1 | 19.4 | 1.69 | 1.66 |
| 6  | 1 | 34.2 | 2.98 | 2.03 |
| 13 | 2 |  9.9 | 1.89 | 1.87 |
| 16 | 2 | 10.8 | 1.45 | 1.31 |
| 17 | 2 | 36.3 | 1.18 | 1.11 |
| 22 | 2 | 32.2 | 1.41 | 1.36 |

The bias estimator's posRMSE gains are consistent but small
(sc6 stands out: 2.98 → 2.03, a 32% per-scenario reduction).

### Caveats

1. **The "truth-AIS" injection is RTK-GNSS in disguise.** That is
   what Helgesen 2022 used for their own calibration; in that
   sense the comparison is apples-to-apples. In *deployment* the
   path to having an AIS-quality anchor without truth is either
   real cooperative AIS (Class-A on the cooperating target) or
   cross-sensor anchoring (item 13 / option 3). The synthetic AIS
   here uses σ = 5 m vs Helgesen's RTK σ ≈ cm — we are arguably
   *less* precise than the paper's anchor, so the comparison is
   not biased in our favour.

2. **The bias estimator's incremental contribution is small (env 1)
   to nil (env 2).** The big driver of the env 2 gap closure was
   AIS, not item 9. If the design intent of item 9 is "calibration
   matters", the empirical answer here is "less than the AIS feed
   itself, on this data". Plausibly the sensors in this fixture
   are already well-mounted (the paper's RTK-truth calibration may
   have been folded into the published detection coordinates), so
   there is little residual offset to learn.

3. **Bit-identity preserved** on every other scenario / config in
   the full 614-test suite. The unanchored autoferry rows are
   identical to the previous (no item 9) baseline.

### Where this leaves us

- Item 9 implementation is correct and validated end-to-end.
- The user's deployment concern ("non-cooperative targets, no
  AIS") is real and is the entry point for **item 13** (cross-
  sensor anchored bias) — that is where the estimator earns its
  keep on deployments where no AIS is available.
- For paper comparisons, the truth-anchor injection is the
  honest way to reproduce Helgesen 2022's calibration setup; with
  it, env 1 matches the paper and env 2 is significantly better.

## 2026-06-15 — Item 9 (inter-sensor registration bias) — shipped but anchor-starved on every available scenario

Implementation landed: `SensorBiasEstimator`, `SensorBiasPairExtractor`,
`ISensorBiasProvider`, Tracker / MhtTracker `setSensorBiasProvider`
hook, `imm_cv_ct_mht_biascal` bench config. 7 new unit tests pin
convergence (20 pair observations → b̂ within 0.3 m of truth), the
range and outlier gates, per-key independence, the bearing variant,
the unobserved-key path, and pair extraction. Full suite (611
tests) green; bit-identical when `bias_provider == nullptr`.

MhtTracker gained `recent_contributions` population (~40 lines)
matching what Tracker.cpp already does — every chosen-leaf hit
appends a SourceTouch with a 2-second sliding window. Without it
the pair extractor saw empty lists; the canonical Tracker pipeline
already populated this. All MHT-style tests, including
`BenchDeterminism.RepeatedSweepProducesIdenticalRows`, stayed green.

**The bench bit-identical result is the real finding.** Bench run
`docs/baselines/biascal_v2_20260615T171638Z.csv` shows every
(scenario, metric) pair bit-identical between `imm_cv_ct_mht` and
`imm_cv_ct_mht_biascal`. The estimator never published a non-zero
bias on any of the 20 scenarios because **no pair observations
were ever emitted**. Two independent reasons:

1. **AutoFerry replay has no AIS.** Grep:
   `adapters/replay/AutoferryJsonReplay.cpp` produces only
   `SensorKind::Lidar / ArpaTtm / EoIr`. There is no AIS feed in
   the replay path. The Helgesen 2022 paper calibrates against
   *RTK-GNSS truth*, which our pipeline doesn't expose as a
   measurement. So the spec's acceptance criterion 4 — "GOSPA env
   1 drops 43 → 35-40 m" — cannot be measured on AutoFerry
   without first solving the anchor-source problem.
2. **Synthetic radars emit RangeBearing2D, not Position2D.**
   `sim/Builders.cpp::makeRangeBearingMeasurement` is the
   ArpaTtm path on synthetics; the extractor's
   `isPositionalNonAnchor` check matches but `SourceTouch.value_enu`
   is only populated by Tracker / MhtTracker for Position2D (the
   range-bearing → ENU projection lives in the estimator, not the
   touch path). So even the synthetic scenarios that *do* have AIS
   yield no AIS-vs-radar pairs.

**Not regressions to investigate; design surface to extend.** The
estimator is correct (unit tests pin convergence) and the wiring
is correct (bit-identity preserved when null, full suite green).
What is missing is the *anchor-source* / *measurement-conversion*
layer between the existing measurement stream and the extractor.

Next options, in priority order:

1. **Synthesize an AIS-style anchor from truth in the AutoFerry
   replay adapter.** That is what the paper does with RTK-GNSS;
   it is not "cheating" any more than the paper is — the bias
   estimator is calibration infrastructure, not a tracker input.
   Smallest delta, most direct test of acceptance criterion 4.
2. **Project RangeBearing2D contributions into ENU before
   appending to SourceTouch**, so synthetic radars feed the
   extractor too. One change to Tracker / MhtTracker; restores
   the synthetic test path.
3. **Track-anchored fallback** (the deferred spec item). Cross-
   sensor anchoring — lidar tracks calibrate radar bias and vice
   versa — sidesteps the cyclic-anchor problem. More invasive.

The implementation is committed (`cae4378`) and the contribution-
population fix to MhtTracker is the follow-up commit. Both
preserve bit-identity on the legacy path. Whether to land (1),
(2), (3) or all three is a scope call for the next session.

Backlog item 9 implementation is DONE; its *measurable benefit
on AutoFerry* awaits an anchor-source extension.

## 2026-06-13 (later 3) — GOSPA metric + Helgesen 2022 reference scaffold

After the item-8 wrap a fair user question landed: how does navtracker
compare to the original AutoFerry paper's own tracker? The dataset's
README pointed at Helgesen, Vasstein, Brekke, Stahl 2022 ("Heterogeneous
multi-sensor tracking for an autonomous surface vehicle in a littoral
environment", *Ocean Engineering* 252 (2022) 111168) whose tracker
(asynchronous multi-sensor VIMM-JIPDA) is essentially what
sota-roadmap.md §2 (JIPDA upgrade) would become — so the paper is the
right reference for "are we as good as the published baseline on the
benchmark we use for ourselves." We did not have the answer.

**Three gaps identified, three fixed:**

1. **Metric mismatch.** Paper uses GOSPA; we used OSPA. Added
   `core/scenario/Gospa.hpp` — greedy GOSPA with default (c, p, α) =
   (30 m, 2, 2) per the GOSPA-on-AutoFerry literature convention.
   8 unit tests pin the boundary cases (matched-pair, missed-only,
   false-only, cardinality growth, α=1, asymmetric). Wired into
   `MetricsResult` (`gospa_mean`, `gospa_p95`) and emitted by
   `Sweep.cpp` alongside OSPA. `gospa_cutoff_m` defaults to 30 m in
   `MetricsParams` — to be reconciled against the paper once we have
   the paper's exact (c, p, α).
2. **No paper reference table.** Added skeleton
   `docs/baselines/helgesen2022_reference.md`. Paper PDF is paywalled
   (Elsevier ScienceDirect) and outside the sandbox network whitelist,
   so the per-scenario columns are placeholders pending manual
   extraction from the published article.
3. **OSPA c=500 compressing harbour-scale diffs.** Backlog item 10
   already flagged this; the per-scenario GOSPA row will make this
   visible (cardinality errors no longer hide under the saturated
   cutoff).

**Paper numbers extracted (Helgesen 2022 §5.8, Tables 6 & 7).**
GOSPA `c = 20 m`, `p = α = 2`, reported as RMS. Aggregated
per-environment (env 1 = sc2-6, env 2 = sc13/16/17/22) not per
scenario. Headline full-fusion (L,R,IR,EO) row:

| Env | Paper GOSPA RMS | Paper posRMSE | Paper Break.L | Paper ANEES |
|---|---:|---|---:|---:|
| 1 (open water)   | 20.37 | 38.91 / 9.43 (Havfruen / Gunnerus) | 86.3 s  | 15.84 |
| 2 (urban channel)| 30.97 | 83.53 / 50.49 (Havfruen / Jetboat) | 200.2 s | 51.90 |

**Bench adjusted to match.** `MetricsParams::gospa_cutoff_m` 30 → 20.
Added `MetricsResult::gospa_rms` (RMS aggregation, paper convention).
`Sweep.cpp` emits `gospa_rms` alongside `gospa_mean` / `gospa_p95`.
Test pin updated (22 → 23 metric rows per scenario).

**Result (`gospa20m_20260613T174620Z`, single seed, canonical
`imm_cv_ct_mht`, c = 20 m).** GOSPA mean and RMS per scenario:

| Sc | env | GOSPA mean | GOSPA RMS | pos_rmse | breaks | lifetime |
|---|---|---:|---:|---:|---:|---:|
| 2  | 1 | 37.5 | 40.9 | 8.6  | 1.5 | 0.958 |
| 3  | 1 | 45.5 | 46.4 | 25.7 | 1.5 | 0.872 |
| 4  | 1 | 40.6 | 42.8 | 11.4 | 0.5 | 0.937 |
| 5  | 1 | 41.2 | 42.4 | 19.4 | 1.5 | 0.913 |
| 6  | 1 | 41.7 | 44.4 | 34.2 | 3   | 0.908 |
| 13 | 2 | 24.2 | 24.6 | 9.9  | 1   | 0.773 |
| 16 | 2 | 27.8 | 28.4 | 10.8 | 1.5 | 0.851 |
| 17 | 2 | 31.0 | 31.3 | 36.3 | 2.5 | 0.902 |
| 22 | 2 | 46.4 | 47.0 | 32.2 | 3.5 | 0.837 |

**Per-env aggregate (RMS-of-per-scenario-RMS, see helgesen2022_reference.md
for caveat):**

| Env | navtracker GOSPA RMS | Paper GOSPA RMS | Δ |
|---|---:|---:|---:|
| 1 | 43.4 | 20.37 | +23 m (≈ 2.1×) |
| 2 | 33.9 | 30.97 | +3 m (≈ 1.1×) |

**Verdict.** navtracker is essentially **on par with the published
baseline on env 2** (urban channel: 33.9 vs 31.0), and **~2× worse on
env 1** (open water: 43.4 vs 20.4). On positional error alone we look
better (pos_rmse env 1 ~ 20 m vs paper's Havfruen 38.91 m driven by
the documented coalescence failure mode); the env 1 GOSPA gap is
therefore cardinality-driven — track breaks dominate the metric, and
the paper's VIMM-JIPDA recovers from misses on something the IMM-MHT
configuration we run does not. Filter consistency (ANEES / nees_mean)
is worse than the paper on both envs and matches what backlog item 12
documents.

Closest algorithmic levers (in priority order):
1. JIPDA upgrade (sota-roadmap §2) — the paper's tracker, the
   single biggest algorithmic-class gap.
2. Inter-sensor registration biases (backlog item 9) — what the
   paper calibrates against RTK-GNSS and we currently do not.
3. NEES calibration (item 12) — honest covariances widen gates and
   reduce the spurious breaks that drive env 1's GOSPA penalty.

The detour is done; item 9 starts next.

## 2026-06-13 (later 2) — JPDA per-sensor (P_D, λ_C) parity: backlog item 8

After the Q-calibration step looked premature (suspects (a) and (b)
shelved, see entries below), stepped back and audited the open backlog
instead of chasing a third NEES knob. Item 8 (JPDA per-sensor parity)
was the cheapest open correctness fix and is a JIPDA prerequisite — the
single-hypothesis JPDA path was still using a single scalar
`(P_D = 0.9, λ_C = 1e-4 m⁻²)` on every measurement regardless of sensor,
silently dimensionally wrong on any scan that mixes radar Position2D
with camera Bearing2D (`λ_C` units differ — m⁻² vs rad⁻¹).

**Change.** `JpdaAssociator` gains a second constructor
`(gate_threshold, ISensorDetectionModel*)`. The scalar ctor is retained
bit-identical. In the per-sensor mode the joint-event log-weight
becomes

```
log w(θ) = Σⱼ [θ(j)==t+1] · (log P_D[s(j)] + log p(z_j|x_t))
        + Σⱼ [θ(j)==0]   · log λ_C[s(j)]
        + Σₜ [t not detected in θ] · Σ_s ∈ S(θ) log(1 − P_D^s(x_t))
```

with `(P_D, λ_C)` resolved per measurement via `model->paramsFor(z)`,
and the per-track miss factor aggregated over distinct
`(sensor, model, source_id)` tuples in the scan via
`missDetectionProbability(...)` — same coverage-conditioned convention
as `TrackTree::branch` in the MHT path. Bench wiring: a
`PerSensorAssociatorFactory` on `benchmark::Config`; when the scenario
declares a `detection_table` the bench passes the model to the
associator constructor, otherwise it falls back to the scalar factory.
Two new ablations: `ekf_cv_jpda_persensor`, `imm_cv_ct_jpda_persensor`.
Three new unit tests pin (a) bit-identity between scalar and uniform-
table single-sensor invocations, (b) per-measurement λ_C isolation
(raising lidar λ_C does not move radar betas), (c) out-of-coverage
miss charges zero penalty.

**Result (`jpda_persensor_20260613T143004Z`, --skip-replays, 3 seeds).**
Synthetic-only first because every synthetic declares its calibrated
per-sensor table and the comparison is the calibrated-vs-uncalibrated
λ_C question directly. Mean OSPA / pos_rmse / id_switches across 3
seeds, persensor − scalar (− is better):

| Scenario | cfg | OSPA Δ | pos_rmse Δ | id_switches Δ |
|---|---|---:|---:|---:|
| crossing | ekf_cv_jpda | −1.7 | −3.7 | 0 |
| head_on | ekf_cv_jpda | −1.7 | −3.7 | 0 |
| dense_clutter | ekf_cv_jpda | +1.3 | −1.7 | **−1.67 (−71%)** |
| crossing_dropout | ekf_cv_jpda | −2.3 | −2.3 | 0 |
| non_cooperative | ekf_cv_jpda | −5.3 | −2.0 | 0 |
| non_cooperative | imm_cv_ct_jpda | −7.3 | **−7.0 (−40%)** | 0 |
| dense_clutter | imm_cv_ct_jpda | +5.3 | −0.3 | −0.33 |
| speed_change | ekf_cv_jpda | −5.3 | −0.3 | +0.33 |

Net: small consistent OSPA wins on most scenarios (4 of 10 statistically
clean improvements, 0 clean regressions on either pipeline). The
dense_clutter signal is the cleanest correctness check — the synthetic
declares 3.33e-5 m⁻² (4 FAs per scan / 600×200 m box, measured), the
legacy scalar used 1e-4; honest λ_C dropped id_switches 71% on EKF/CV.
The non_cooperative win (pos_rmse −7 m on the IMM, −40%) is the
dimensional-units fix in action: bearing-only with calibrated 1e-2 rad⁻¹
instead of mismatched 1e-4 m⁻². No clean-synthetic regression on either
pipeline.

**Replay (autoferry × 9 + philos, single-seed,
`jpda_persensor_20260613T142623Z`).** Honest read: mixed. Lifetime
preserved everywhere (within ±0.025 on every replay scenario), so no
risk to drop in. OSPA / id_switches reshuffle: clean wins on some
scenarios (sc22 OSPA −7.7 EKF / −6.3 IMM; sc17 −5.7 EKF / −5.7 IMM,
id_sw −8 IMM; sc2 id_sw 24→18.5 EKF / 16→16.5 IMM; sc6 id_sw 30→18.5
EKF), clean losses on others (sc3 id_sw +6 EKF / +7.5 IMM; sc13 pos_rmse
+4 EKF / +9 IMM; sc16 id_sw +7 EKF / +14 IMM; philos pos_rmse +13 m
EKF / +8 m IMM). The pattern matches backlog item 4's recorded lesson:
where the clutter is truly Poisson (clean synthetics, sc22, sc17) the
calibrated table is the right operating point; where it isn't (urban
shoreline structure on sc13/sc16, persistent unmatched plots on philos),
the honest per-sensor λ pays the same urban-camera penalty the MHT
path absorbs via VIMM + clutter map and the single-hypothesis JPDA
doesn't have those buffers. NEES moves with bigger amplitude — most
scenarios improve modestly (sc6 EKF 82 → 56; sc22 IMM 240 → 119) but
sc22 EKF blows up (27 → 6954, camera-dominated, no IMM mode-switching
to dilate R against bursty residuals). Bottom line: the math is right,
but the *single-hypothesis* JPDA path was relying on the wrong-but-
forgiving scalar λ_C to smooth over upstream model mismatch — the same
upstream mismatch the MHT canonical config already absorbs.

**Decision.** Keep both `*_persensor` configs as opt-in ablations
(promoted into the canonical bench matrix, not into the canonical
configs). The canonical JPDA configs stay on scalar λ_C as the
pre-JIPDA baseline; the upgrade target is JIPDA proper
(sota-roadmap.md §2), where per-track existence and IMM mode-aware R
provide the buffers the synthetic-only per-sensor wins demonstrate are
needed before flipping the default.

**Implementation footnote.** First bench attempt segfaulted in
`FixedSensorDetectionModel::paramsFor`. Root cause: the bench loop's
`std::shared_ptr<ISensorDetectionModel> det` was scoped inside an
`if` block, so the JPDA's raw pointer dangled by the time the tracker
ran. Hoisting the shared_ptr to the outer scope (so its lifetime spans
the tracker) fixed it — same lifetime pattern the MHT path already
uses. `result.p_d` is set to the homogeneous-batch sensor's P_D when
all measurements share a `(sensor, model, source_id)` tuple, else 0
(IMM falls back to its unnormalized mixture-likelihood proxy). True
per-track P_D for mixed batches is deferred to JIPDA where it lives
naturally as per-track existence.

**Decision.** Promote both per-sensor ablations into the canonical bench
matrix; do not flip the canonical configs (`ekf_cv_jpda` /
`imm_cv_ct_jpda`) yet — the JIPDA upgrade (sota-roadmap.md §2) will
re-architect the JPDA path with per-track existence, and the scalar
configs stay as the pre-JIPDA baseline for that comparison. Backlog
item 8 closes; next up is item 9 (inter-sensor registration biases) —
the "combination of different sensors" thread.

## 2026-06-13 (later) — Bearing range-variance guard measured: not the lever

Implemented the classical BOT bearing range-variance guard (Aidala-
style, post-update LOS clamp) as `imm_cv_ct_mht_bearguard` ablation
(commit `03e16ee`). Math correct, unit tests pass, full ctest 592/592
green. Re-ran the bench (`docs/baselines/bearguard_20260613T111159Z.csv`,
3 seeds, 14 configs × scenarios).

**Result — guard does not move sc5 NEES meaningfully:**

| Config | sc5 nees_mean | β̂ | OSPA | id_sw |
|---|---:|---:|---:|---:|
| `imm_cv_ct_mht` (default, no guard) | 79.01 | 39.5 | 414 | 91 |
| `imm_cv_ct_mht_bearguard` (guard on) | 78.44 | 39.2 | 420 | 92 |
| Δ | **−0.7 %** | −0.7 % | +1.5 % | +1 |

Clean synthetics: bit-identical (1.51171 → 1.51171 across all 5
seeds). The guard fires only on `Bearing2D`, so position-only
synthetics never trigger it.

**Why it doesn't help on sc5 (re-read the NIS table):**

Cameras have ε̄ⁿⁱˢ = 0.30 (IR) and 0.43 (EO) — bearing innovations are
1.6–1.8× tighter than R predicts. That means the EKF gain K is tiny
(R dominates S 10×), so the Joseph posterior barely changes P. The
along-LOS collapse mechanism the guard targets is never large enough
to clamp.

**Real driver of sc5 overconfidence (refined diagnosis):** the radar
NIS regime `(α̂=2.17, trace_ratio=4.02)` puts tr(HPHᵀ) at 4× tr(R)
on every Position2D update — P_xy is too tight *at the moment a
radar update arrives*. Cameras don't shrink P (tiny K), so the
tightening must come from somewhere else. Sequence:

1. Radar at scan t₀ → P_xy posterior is OK.
2. ~0.4–1.6 s of bearing updates (16 Hz EO/IR) follow, K ≈ 0, P_xy
   essentially unchanged.
3. Predict step grows P_xy by Q·Δt — but only by Q·Δt.
4. Radar at scan t₁ arrives. If Q is small relative to actual
   harbour maneuvering, the predicted P_xy is still much smaller
   than the true posterior should be → high radar NIS, high
   position NEES.

So the working hypothesis is now **process-noise calibration**:
`kImmCv5AccelPsd = 0.5 m²/s³` and `kImmCtAccelPsd` are tuned for
synthetic CV/CT, not for real harbour maneuvering. Q is the only
mechanism that grows P between updates; the data points there.

**Decision:** keep `imm_cv_ct_mht_bearguard` as an opt-in ablation
(the math is correct and the BOT pathology is real in principle; the
guard costs essentially nothing when it's a no-op) but **do not**
promote to default. Move on to Q calibration as the next item-12
suspect (c — explicitly listed in the spec). Wire AutoFerry NEES as
the lever and sweep Q PSDs; measure sc5 nees_mean directly.

## 2026-06-13 — NEES/NIS first run, sc5 diagnosis confirmed, R suspect refined

First bench with the `IInnovationSink` port wired (commit `5b13242`).
13 configs × (synthetic + replay) × seeds, full sweep. Captured into
`docs/baselines/consistency_v1_20260613T083231Z.csv`.

**Acceptance criteria (per spec
`2026-06-13-nees-r-calibration-design.md`):**

| Criterion | Result |
|---|---|
| Clean synthetic crossing under canonical MHT, `nees_mean ∈ [1.5, 3.0]` | ✅ 1.40 – 2.18 across 5 seeds (mean 1.69; seed 2 at 1.40 is the only sub-floor, within seed noise) |
| AutoFerry sc5 `nees_mean ≫ 2`, reproducing item-12 diagnosis | ✅ **79.01** (β̂ = 39.5) on `imm_cv_ct_mht` — matches the 2026-06-12 forensics (77.6 mean, β̂ ≈ 39) bit-exactly from a clean rebuild |
| No regressions in OSPA / lifetime / RMSE / id_switches | ✅ Full ctest 589/589 green |
| Determinism preserved | ✅ Existing `BenchDeterminism.RepeatedSweepProducesIdenticalRows` still passes |

**NEW finding — the R suspect refines.** Item 12's hypothesis was
"camera bearing R too small." The per-sensor sc5 NIS table says the
opposite for cameras and points the finger at the position-update
path instead:

| Source (sc5, `imm_cv_ct_mht_ipda`) | N | ε̄ⁿⁱˢ | α̂ | tr(HPHᵀ)/tr(R) | coverage_95 |
|---|---:|---:|---:|---:|---:|
| arpattm Position2D (radar) | 377 | 4.34 | 2.17 | 4.02 | 0.72 |
| eoir Bearing2D (EO camera) | 6857 | 0.43 | 0.43 | 0.11 | 0.99 |
| eoir Bearing2D (IR camera) | 16895 | 0.30 | 0.30 | 0.07 | 1.00 |
| lidar Position2D | 580 | 3.45 | 1.73 | 1.60 | 0.79 |

Both cameras have ε̄ⁿⁱˢ ≪ 1 with trace_ratio ≪ 1: R *dominates* S by
~10× and the actual residuals are 3-7× smaller than R predicts.
Cameras are if anything **over**-pessimistic on R, not under. The
overconfident-S signal lives entirely on the position sensors —
radar and lidar — and tr(HPHᵀ)/tr(R) ≥ 1.6 there says the *state*
covariance HPHᵀ dominates, so the high NIS reflects too-small P
rather than too-small R.

Mechanistically this is **suspect (b)** in item 12 — bearing-update
range collapse on the 16 Hz EoIR stream squeezing the radar/lidar's
range-direction covariance to overconfidence — measured directly,
before we even tried suspect (a). The implication for fix
sequencing:

1. **Skip the camera-σ_bearing calibration step.** The data says
   it's not the lever — cameras are over-pessimistic, not
   under-pessimistic, and shrinking R would make NEES worse.
2. **Move straight to the bearing range-variance guard
   (suspect b).** Add the "range-direction variance must be
   non-decreasing under a `Bearing2D` update" invariant in the
   estimator. Expected effect on sc5: position NIS for radar/lidar
   drops toward consistent (the camera floods stop collapsing
   range cov), nees_mean drops sharply.
3. **Position-sensor R may also need a small inflation** (α̂_radar
   = 2.17; α̂_lidar = 1.73) but only after (2) — those numbers
   include both the R-mistuning and the P-collapse effects, and (2)
   will redistribute them.

**Cross-tracker picture.** Single-Gaussian paths (GNN/JPDA) on sc5:
β̂ = 3-12 (moderate overconfidence). MHT path: β̂ = 37-40 (severe).
Confirms the conveyor mechanism is MHT-specific — the branching
through bearing-only hits is where range collapses fastest.

The instrumentation lands the diagnosis. The fix is now the bearing
range-variance guard, scoped per the backlog item 12 hand-off.

## 2026-06-01 — UKF vs EKF baseline (4 scenarios)

Filter swapped behind the `IEstimator` port; everything else identical
between the two runs. Source: `tests/scenario/test_filter_comparison.cpp`.

| Scenario | Filter | mean OSPA (m) | ID switches | Final tracks |
|----------|--------|---------------|-------------|--------------|
| SingleStraightLine (20 steps, σ=5 m) | EKF | 4.9904 | 0 | 1 |
| SingleStraightLine | UKF | 4.9904 | 0 | 1 |
| ParallelTargets (30 steps, σ=5 m, 800 m apart) | EKF | 4.1646 | 0 | 2 |
| ParallelTargets | UKF | 4.1646 | 0 | 2 |
| Crossing (40 steps, σ=8 m, 20 m offset at crossing) | EKF | 7.1620 | 0 | 2 |
| Crossing | UKF | 7.1620 | 0 | 2 |
| AisDropout (5 → 7 s gap → 9 steps, σ=5 m) | EKF | 5.5534 | 0 | 1 |
| AisDropout | UKF | 5.5534 | 0 | 1 |

**Takeaway.** Bit-identical to 4 decimals on every scenario. Reason: every
scenario uses Position2D measurements (linear `h`); on linear `h` the UKF
posterior equals the Kalman posterior by construction (Wan–van der Merwe).
The current scenario suite **cannot** differentiate kinematic-filter
choices. Distinguishing UKF (and later particle / IMM) from the EKF requires
a scenario where the measurement function is materially nonlinear:
short-range range/bearing, bearing-only, or rapid range-rate. That scenario
is not built yet.

**What this means for the next filter (particle).** Building a
short-range range/bearing scenario with appreciable prior position
uncertainty is a prerequisite for any meaningful comparison. Without it
every estimator we add will show identical numbers and we'll learn nothing.
Recommend adding that scenario to `core/scenario/Builders.hpp` before or
alongside the particle filter.

## 2026-06-01 — UKF vs EKF on range/bearing pass scenarios

New builder `buildRangeBearingPassScenario` (initial Position2D seed →
RangeBearing2D thereafter, sensor at ENU origin). Two configurations:

| Scenario | Geometry | Filter | mean OSPA (m) | Δ vs EKF |
|----------|----------|--------|---------------|----------|
| ShortRangePass | CPA ≈ 50 m, σ_r=10 m, σ_β=5° | EKF | 8.6976 | — |
| ShortRangePass | as above | UKF | 8.6308 | −0.068 m (−0.8%) |
| VeryShortRangePass | CPA ≈ 20 m, σ_r=20 m, σ_β=10° | EKF | 17.2779 | — |
| VeryShortRangePass | as above | UKF | 16.1210 | −1.157 m (−6.7%) |

**Takeaway.** UKF advantage is real and **scales with nonlinearity
intensity**, as theory predicts. The mild-nonlinearity case (CPA 50 m, small
noise) shows a ~1% improvement — near the noise floor of a single-seed run
and likely not worth the extra cost in production. The sharper case (CPA
20 m, large noise) shows ~7% — the EKF's first-order linearization across
the closest-approach geometry materially diverges from the unscented
treatment.

**Implication.** Quoting a single "UKF vs EKF" number is misleading; the
ratio depends entirely on how close to the sensor the geometry gets and how
much measurement and prior uncertainty there is. For realistic maritime
scenarios where vessels stay >1 km from sensors, the gap will be small. For
harbor-proximity, docking, or close passes, the gap matters.

**Methodology notes.** Single fixed seed per scenario, so the absolute
numbers carry single-realization noise. A proper comparison would average
over multiple seeds and report a confidence interval — that's a documented
next step. Two configurations is a thin sample; widening to a sweep of CPAs
and noise levels would let us draw the EKF→UKF transfer curve quantitatively.

## 2026-06-01 — PF vs EKF vs UKF on range/bearing pass scenarios

`ParticleFilterEstimator` with `N=1000`, `ess_fraction=0.5`,
`init_speed_std=10`, seed = scenario seed. Same scenarios, gates, and
thresholds as the previous entry.

| Scenario | Filter | mean OSPA (m) | Δ vs EKF |
|----------|--------|---------------|----------|
| ShortRangePass | EKF | 8.6976 | — |
| ShortRangePass | UKF | 8.6308 | −0.068 m (−0.8%) |
| ShortRangePass | PF  | 9.9828 | +1.285 m (+14.8%) |
| VeryShortRangePass | EKF | 17.2779 | — |
| VeryShortRangePass | UKF | 16.1210 | −1.157 m (−6.7%) |
| VeryShortRangePass | PF  | 16.4674 | −0.811 m (−4.7%) |

**Takeaway.** The PF lands *behind* both Kalman variants on the mild
nonlinearity scenario and *between* them on the sharper one. This is the
expected outcome for a bootstrap PF on a unimodal posterior: with N=1000
particles and a 4-D state the Monte-Carlo variance of the weighted mean is
non-negligible, and there is no offsetting structural advantage when the
true posterior is well-approximated by a Gaussian. The UKF's `2n+1 = 9`
sigma points capture the second-moment correction at a tiny fraction of the
runtime cost.

The PF's theoretical advantage — representing non-Gaussian or *multimodal*
posteriors — is not exercised by either of these scenarios. Both pass
geometries produce a posterior that converges to a single mode once range
information accumulates over a few updates. To see the PF win against the
UKF we need a scenario where the posterior is genuinely multimodal: a
**bearing-only** track, a target near closest approach with high prior
position uncertainty, or two targets whose individual posteriors overlap
significantly. Documented as the next scenario to build.

**Methodology notes.** Single seed per filter, N=1000, ESS threshold 0.5·N.
The PF runs to completion in tens of milliseconds for these scenarios, so
runtime is not a current concern. Multi-seed averaging is still the right
next step before quoting absolute numbers — single-seed deltas of <1 m are
within Monte-Carlo noise for N=1000. The 14.8% gap on ShortRangePass is
large enough that it would survive averaging, but the 4.7% gap on
VeryShortRangePass is borderline.

**Open follow-ups.** (1) Build a bearing-only or close-approach scenario
where the posterior is provably multimodal. (2) Sweep `N ∈ {200, 500, 1000,
2000, 5000}` to characterize the variance/cost trade. (3) Refactor
`MeasurementModels` so the PF update path does not allocate a throwaway
Jacobian `H` per particle (noted in the code-review of Task 5).

## 2026-06-01 — Multi-seed N-sweep on ShortRangePass

Same scenario as before, but each `(filter, seed)` cell rerun for 20 seeds
to convert single-realization deltas into mean ± standard deviation.

Source: `tests/scenario/test_filter_comparison.cpp` ::
`FilterComparison.ShortRangeMultiSeedSweep` (seeds 41–60).

| Filter / Config | mean OSPA (m) ± stddev |
|-----------------|------------------------|
| EKF             | 9.2929 ± 1.4251 |
| UKF             | 9.2467 ± 1.4377 |
| PF, N=200       | 16.5884 ± 10.2107 |
| PF, N=500       | 10.6783 ± 4.5291 |
| PF, N=1000      | 10.0169 ± 1.5601 |
| PF, N=2000      | 9.8517 ± 1.9292 |

**Takeaway, retraction.** The previous entry quoted a 0.8% UKF advantage on
ShortRangePass from a single seed. The 20-seed average **vacates** that
claim: UKF beats EKF by **0.05 m (≈ 0.5%)** which is well within
single-realization noise (1.4 m). On a unimodal Position+range/bearing
posterior at moderate range, EKF and UKF are statistically indistinguishable
on this scenario. The single-seed VeryShortRangePass UKF advantage (6.7%)
likely survives averaging but is not yet re-measured.

**Particle filter cost / accuracy frontier.** The PF requires roughly N=1000
to come within ~8% of the UKF and N=2000 to come within ~6%. At N=200 it is
catastrophically noisy (16.6 ± 10 m), meaning the bootstrap PF needs
sufficient particle count for *minimum* viability before the trade-off
discussion even starts. This is the expected story for a bootstrap PF on a
Gaussian-ish posterior: no structural advantage to redeem the Monte-Carlo
variance. Adaptive `N` or a more sophisticated PF variant (auxiliary,
marginalized) is the next thing to try if PF is to be competitive at lower
N.

## 2026-06-01 — Bearing-only pass scenario (stationary sensor)

New scenario builder `buildBearingOnlyScenario` + new measurement model
`MeasurementModel::Bearing2D` (scalar `β = atan2(py, px)`, 1×4 Jacobian).
Sensor at ENU origin, **stationary**. Initial Position2D seed with σ=80 m
(wide), then 60 s of bearing-only measurements with σ=3°.

| Filter | mean OSPA (m) (seed 71) |
|--------|--------------------------|
| EKF | 181.85 |
| UKF | 183.26 |
| PF, N=2000 | 183.66 |

**Takeaway.** All three filters are statistically indistinguishable on this
scenario. The expected PF advantage (representing a non-Gaussian
banana-shaped posterior) is **not realized** here, because from a stationary
sensor with no own-ship motion the **range channel is genuinely
unobservable** — there is no information in any bearing sequence that
recovers range. The posterior on range stays as wide as the prior allowed,
and OSPA is dominated by the along-bearing position error that no estimator
can fix. The PF correctly maintains the spread rather than artificially
collapsing it, which is the right behaviour but invisible in OSPA.

**Implication.** Bearing-only is *not* automatically a PF-favouring
scenario. The PF only beats a Kalman filter when the posterior is genuinely
non-Gaussian AND the data carries enough information to localize the true
mode. To exercise the PF's real advantage we need one of:
1. **Own-ship motion** — moving sensor → parallax → range becomes weakly
   observable; intermediate posteriors are banana-shaped.
2. **Crossed bearings** from a second sensor with known offset — produces a
   bimodal prior that collapses to one mode as more data arrives.
3. **Maneuvering target with known constraint** (e.g. confined to a
   channel) breaking the bearing-only symmetry.

All three are substantial scenario work and require a sensor-frame abstraction
the codebase does not yet have. Documented as the next scenario investment.

**Open follow-ups (carried forward).** (1) Build a scenario with own-ship
motion to make bearing-only range observable. (2) Sweep the PF on
VeryShortRangePass over 20 seeds to confirm whether the 6.7% UKF advantage
survives averaging. (3) Auxiliary or regularized PF variants to reduce the
N required for viability.

## 2026-06-01 — IMM (CV+CT, EKF backend) vs EKF/UKF/PF on maneuvering target

`ImmEstimator` with K=2 (`ConstantVelocity5State` + `CoordinatedTurn`), EKF
backend per mode, transition matrix `[[0.95, 0.05], [0.10, 0.90]]`,
initial mode probabilities `[0.5, 0.5]`, `q_a = 0.5`, `q_ω = 0.1` (CT) and
`0.01` (CV5). Scenario: target moves straight for 5 s, turns at 0.2 rad/s
for 5 s, straight for 5 s. Position2D measurements at 1 Hz, σ = 5 m.
Source: `tests/scenario/test_filter_comparison.cpp::FilterComparison.ManeuveringTarget`.

| Filter | mean OSPA (m) |
|--------|----------------|
| EKF (CV2D)        | 6.5871 |
| UKF (CV2D)        | 6.5871 |
| PF  (CV2D, N=1000)| 6.7230 |
| IMM (CV5 + CT)    | 6.5871 |

**Takeaway.** IMM ties EKF and UKF exactly to four decimals. This is **not
a measurement-noise-floor effect** — a sharper diagnostic scenario
(`ω = 0.5 rad/s`, σ = 1 m, dt = 0.5 s, 8 s turn) gave EKF=UKF=IMM=1.9767
with PF=41.0334 (collapsed). The IMM's CT-mode probability is observed to
**decline monotonically** from its initial 0.5 throughout the run, reaching
0.334 at the end — the CT mode is never activated, regardless of how
sharp the turn is.

**Diagnosis (not a bug).** With `Position2D`-only measurements the
linearized `H` has zero in the `ω` column, so `ω` is unobservable by the
EKF update. Both CV and CT modes converge their `ω_mean` to 0, making
their predicted positions essentially identical, so their likelihoods are
indistinguishable. The transition-matrix prior (CV self-loop 0.95 vs
CT self-loop 0.90) then drives the mode probability monotonically toward
CV. The IMM algorithm is correct — it's the position-only + EKF-backend
+ symmetric-2-mode configuration that has no observability path.

**Implication.** The current IMM is correctly built and unit-tested, but
it does not win against single-model CV on the position-only scenarios we
have. To see IMM win on position-only measurements, implement
**prescribed-rate three-mode IMM** (`CV + CT(+ω̂) + CT(−ω̂)`) — the
classic maritime configuration. This is captured as the next IMM step in
`docs/algorithms/estimation.md` § 6 "Known limitation".

**Methodology notes.** Single seed (91), single scenario, single
configuration. With IMM tied to the single-mode baseline, multi-seed
averaging does not change the conclusion; no sweep was run.

## 2026-06-01 — Three-mode IMM (CV + prescribed CT±) on maneuvering target

`PrescribedTurn(omega_const, q_a, q_omega)` motion model: fixed turn rate
at construction, otherwise identical to `CoordinatedTurn`. Three-mode IMM
configuration: `{CV5State(0.5, 0.001), PrescribedTurn(+0.2, 0.5, 0.001),
PrescribedTurn(-0.2, 0.5, 0.001)}`, transition matrix
`[[0.90,0.05,0.05],[0.10,0.85,0.05],[0.10,0.05,0.85]]`, initial mixture
`[0.34, 0.33, 0.33]`. Same maneuvering scenario as the previous IMM entry
(5 s straight + 5 s turn at +0.2 rad/s + 5 s straight; 1 Hz Position2D,
σ = 5 m, seed 91).

Source: `tests/scenario/test_filter_comparison.cpp::FilterComparison.Maneuvering3ModeIMM`.

| Filter | mean OSPA (m) | Δ vs EKF |
|--------|----------------|----------|
| EKF (CV2D)                          | 6.5871 | — |
| IMM-2 (CV5 + free-ω CT)             | 6.5871 | 0.0 (0%) |
| IMM-3 (CV5 + CT(+0.2) + CT(-0.2))   | **6.0973** | **−0.4898 (−7.4%)** |

**Takeaway.** First IMM configuration to actually beat the EKF baseline
on any scenario in this codebase. The mechanism is exactly the one
predicted in the prior entry's diagnosis: `CT(+0.2)` matches the true turn
rate, so during the 5-second turn its predicted positions track truth
while the CV mode's predicted positions diverge. The mode-probability
update shifts mass to `CT(+0.2)`, the mixture projection uses it more,
and OSPA drops. `CT(-0.2)` stays quiet (its predicted positions diverge
even more than CV's during a left turn).

The 7.4% number is bounded by the fact that the maneuver is only 5/15 of
the scenario duration. Restricting OSPA to just the turn-segment timesteps
would show a much larger gap; the cross-segment average is what we report
for direct comparability with the prior IMM-2 entry.

**Implication.** Prescribed-rate IMM is the right baseline for maritime
maneuver tracking with position-only AIS/Position2D inputs. The free-ω
single-CT IMM-2 should be considered a curiosity rather than a useful
configuration when measurements don't observe ω.

**Methodology notes.** Single seed (91). Multi-seed averaging would tighten
the 7.4% claim but the directional result (IMM-3 < EKF, IMM-2 ≈ EKF) is
robust by construction — the prescribed-rate CT has a structural advantage
the other modes cannot offer.

**Open follow-ups.** (1) Multi-seed sweep on this scenario. (2) Sweep over
maneuver rate ω_true with fixed prescribed ω̂ to characterize the
sensitivity (how close does ω̂ have to match ω_true for IMM-3 to win?).
(3) Wider mode bank, e.g. `CV + CT(±0.1) + CT(±0.2) + CT(±0.5)`.
(4) UKF backend per mode to let a single free-ω CT mode work via
sigma-point propagation through F (replaces prescribed rates).

## 2026-06-01 — JPDA vs GNN on clutter-crossing scenario

`JpdaAssociator(gate=20, P_D=0.9, λ_C=1e-4)` vs
`GnnAssociator(gate=20)`. Same backend (`EkfEstimator` with
`ConstantVelocity2D(0.1)`), same lifecycle thresholds. Scenario:
`buildClutterCrossingScenario` — two CV targets crossing at the origin
plus 4 uniform false alarms per scan in [−300, 300] × [−50, 50], target
measurement σ = 5 m, 30 scans, seed 31. Run via `runScenarioBatched`.

Source: `tests/scenario/test_jpda_comparison.cpp::JpdaComparison.ClutterCrossing`.

| Associator | mean OSPA (m) | ID switches | Final tracks |
|------------|----------------|-------------|---------------|
| GNN  | 47.3286 | **11** | **35** |
| JPDA | 45.9158 | **4**  | **14** |

**Takeaway.** JPDA's primary value is identity stability and clutter
rejection, not localization accuracy. ID switches drop **64%** (11 → 4)
and final track count drops **60%** (35 → 14). The OSPA improvement is
modest (~3%) because OSPA is clipped at the cutoff (50 m) and the GNN's
errors are largely identity errors (track-swap at crossing) rather than
position errors — the cutoff masks them. The right metric for this
comparison is ID switches, not OSPA.

The 35-track count for GNN reflects clutter contamination — each scan's
4 false alarms have nonzero probability of being the closest in-gate
measurement to some track, kicking GNN's hard assignment to a clutter
point and seeding a new track when the next scan's real measurement
fails to match the contaminated old track. JPDA's soft update spreads
mass across all in-gate measurements weighted by likelihood; clutter
measurements contribute near-zero weight to real tracks and the new
tracks they would seed get suppressed by the M-of-N confirmation policy.

**Methodology notes.** Single seed (31). Multi-seed sweep would
strengthen the OSPA number but the ID-switch reduction is structural
(it follows from JPDA's contamination resistance, not from one lucky
seed) and should survive averaging. The clutter density (~ 4 false
alarms per scan over a 600×100 m box) is moderate; sweeping density up
should widen JPDA's advantage further. Runtime: enumeration cost is
negligible at 2 tracks × ~6 gated measurements per scan.

**Open follow-ups.** (1) Multi-seed × multi-clutter-density sweep.
(2) JIPDA (Integrated PDA) — adds per-track existence probability,
ties into M-of-N. (3) K-best joint events for cluster sizes beyond
~6×6. (4) MHT, the natural next step in the hypothesis-deferment line.

## 2026-06-01 — GNN / JPDA / MHT on crossing-with-dropout scenario

`MhtTracker` (P_D=0.9, λ_C=1e-4, gate=9.0, N_scan=3, K_max_leaves=5,
score_delete=−15.0) vs `JpdaAssociator(gate=9, P_D=0.9, λ_C=1e-4)` vs
`GnnAssociator(gate=9)`. Shared EKF backend
(`EkfEstimator + ConstantVelocity2D(0.1)`). Scenario:
`buildCrossingDropoutScenario(vx=4, y=1, noise=1, dropout=[13, 17), seed=113)`
— two targets cross with ~2 m closest approach, sensor blacks out for
4 consecutive scans across the crossing.

Source: `tests/scenario/test_mht_comparison.cpp::MhtComparison.CrossingWithDropout`.

| Associator | mean OSPA (m) | ID switches | Final tracks |
|------------|----------------|-------------|---------------|
| GNN  | 7.2684 | 3 | 3 (1 ghost) |
| JPDA | 7.2667 | 2 | 3 (1 ghost) |
| **MHT**  | **1.0501** | **0** | **2 (correct)** |

**Takeaway.** Largest single-scenario win in the codebase. MHT preserves
identity through the 4-scan dropout where both single-scan associators
commit too early at the crossing, swap identities, and leave ghost
tracks behind. The 7× OSPA gap is not a tuning artifact — it reflects
the *structural* limit of any per-scan decision rule against a problem
where the right answer is only knowable after seeing post-dropout
measurements. GNN and JPDA are nearly tied (7.27 vs 7.27): JPDA's soft
update doesn't help when both targets are equally likely under any
hypothesis until the dropout ends and trajectories disambiguate.

This is the first scenario where MHT's added complexity over JPDA is
clearly worth it. On the clutter-crossing scenario where the right
answer is locally available each scan (JPDA's 64% ID-switch reduction
already captures most of the value), MHT would not pay off comparably.

**Methodology notes.** Single seed (113). The dropout length (4 scans)
is matched to `N_scan = 3` so the MHT trunk extends exactly through the
gap. Lengthening the dropout beyond `N_scan` would force MHT to commit
during the blackout and erase its advantage. Sensitivity sweep documented
as future work.

**Open follow-ups.** (1) Multi-seed sweep on this scenario to tighten
the OSPA number (the 7× ratio is unlikely to budge much under
averaging — it's structural — but worth confirming). (2) Sensitivity
sweep over `(dropout_length, N_scan, closest_approach)` to characterize
the regime where MHT dominates. (3) K-best global non-conflict via
Murty's — the largest expected improvement to MHT itself. (4) IMM-backed
MHT for maneuvering targets across ambiguous gaps. (5) Murty + JIPDA
hybrid (track existence probability + hypothesis tree) as the
eventual high-end maritime tracker.

## 2026-06-01 — Bearing-only with moving sensor (parallax) — PF wins

`Measurement.sensor_position_enu` is now wired through every estimator and
associator's measurement-model call path. The new scenario builder
`buildBearingOnlyMovingSensorScenario` emits an initial wide-covariance
Position2D seed (σ = 300 m) followed by 60 s of `Bearing2D` measurements
(σ = 1.5°) from a sensor moving +y at 10 m/s **perpendicular to the
line-of-sight** to a stationary target at (1500, 0). Sensor sweeps from
(0, −300) to (0, +300), producing ~22° of bearing change against the
1.5° measurement noise (~15:1 parallax SNR). Wide initial range prior
keeps the posterior in the non-Gaussian regime during the first ~15 s
of convergence.

Source: `tests/scenario/test_filter_comparison.cpp::FilterComparison.BearingOnlyMovingSensor`.

| Filter | mean OSPA (m) | Δ vs EKF |
|--------|----------------|----------|
| EKF (CV)         | 181.6201 | — |
| UKF (CV)         | 185.4117 | +3.79 (+2.1%) |
| **PF (CV, N=2000)** | **123.1583** | **−58.46 (−32.2%)** |

**Takeaway.** First scenario in the codebase where the PF demonstrably
beats both Gaussian filters. The mechanism is exactly what theory
predicts: with proper parallax geometry (sensor motion perpendicular to
LOS) and a wide initial range prior, the posterior on `(px, py)` is
genuinely banana-shaped during the early convergence window — the
crescent of (bearing line) ∩ (broad range prior). EKF and UKF
moment-match this into a Gaussian ellipse and accumulate error; the PF
retains the actual non-Gaussian shape through the transient and gets
substantially better position estimates.

UKF is slightly worse than EKF here, consistent with sigma-point
sampling error mildly exceeding linearization error at this nonlinearity
level. Both Kalman variants sit at ~180 m OSPA because they collapse the
banana to an axis-aligned ellipse around the centroid, which is far from
the actual posterior mode early on.

The first-attempt geometry (sensor moves along LOS at (0, 0) toward
target at (1000, 100)) gave only ~2.4° of bearing sweep against 3° noise
and produced a PF *loss* (112.87 vs 100.12 for EKF). That null result
demonstrated the prerequisite: parallax SNR has to exceed measurement
noise by a meaningful margin for the non-Gaussian regime to manifest.
The retuned geometry above passes that bar comfortably.

**Methodology notes.** Single seed (137), N=2000 particles. Multi-seed
sweep is the straightforward next step. The PF win should survive
averaging because the geometry advantage is structural, not seed-dependent.

**Open follow-ups.** (1) Multi-seed sweep to tighten the 32% claim.
(2) Sweep over sensor velocity (slower = less parallax = PF should win
by more, until the parallax disappears entirely). (3) Slowly-moving
target variant. (4) Closer target ((500, 0) instead of (1500, 0)) —
geometry remains in the non-Gaussian regime longer, gap should grow.
(5) Use this scenario harness to test JPDA / MHT with bearing-only
measurements once the soft-update / branching paths support
non-position measurement models.

**Honest summary of the PF story.** Across three bearing-only attempts:
- Stationary sensor, position-only-seed prior: PF tied EKF/UKF
  (~182 m all, range unobservable from a stationary sensor — documented
  earlier).
- Moving sensor, sensor motion **along** LOS: PF *worst* by 12 m
  (parallax SNR too low — first attempt above).
- Moving sensor, sensor motion **perpendicular** to LOS, wide prior:
  PF wins by 32% — the textbook geometry, finally exercised.

The PF advantage was always conditional on geometry that lets the
non-Gaussian posterior actually form. The first two scenarios didn't
provide that; the third does.

## 2026-06-01 — Multi-seed sweep on the four "wins" (retraction + confirmations)

Re-ran the four winning comparison scenarios with 20 seeds each (seeds
201..220, same set across scenarios) to convert single-realization
deltas into mean ± stddev. Source:
`tests/scenario/test_multi_seed_sweep.cpp`.

### IMM-3 on Maneuvering — **confirmed**

| Filter | mean OSPA ± stddev (m) | mean ID switches |
|--------|--------------------------|------------------|
| EKF (CV)   | 5.6713 ± 0.9093 | 0.00 |
| IMM-2      | 5.6713 ± 0.9093 | 0.00 |
| IMM-3      | **4.8148 ± 0.5916** | 0.00 |

Confidence intervals do not overlap. The 7.4% single-seed delta tightens
to ~15% in expectation (≈0.86 m), and IMM-3's stddev is also smaller
than EKF's, indicating the prescribed-CT modes reduce *variability* in
addition to mean error. EKF and IMM-2 are bit-identical to 4 decimals
because position-only measurements collapse the 5-state-CV and free-ω-CT
posteriors into the same predicted positions (no information channel to
distinguish ω modes — same observability gap documented earlier).

### JPDA on ClutterCrossing — **confirmed, very cleanly**

| Filter | mean OSPA ± stddev (m) | mean ID switches |
|--------|--------------------------|------------------|
| GNN  | 47.3207 ± 0.1141 | 9.90 |
| JPDA | **45.3199 ± 0.4377** | **2.45** |

OSPA intervals barely overlap; ID-switch advantage is enormous and
robust (9.90 → 2.45 mean across 20 seeds = ~75% reduction, larger than
the original single-seed 64% claim). Strongest and most defensible win
in the codebase.

### MHT on CrossingDropout — **retracted**

| Filter | mean OSPA ± stddev (m) | mean ID switches |
|--------|--------------------------|------------------|
| GNN  | 1.9659 ± 1.9014 | 0.70 |
| JPDA | 1.9656 ± 1.9017 | **0.20** |
| MHT  | 1.9656 ± 1.9010 | 0.90 |

**The 7× MHT win was a single-seed artifact.** Averaged over 20 seeds,
all three associators land at the same OSPA (1.966) with the same
±1.9 m noise floor. The stddev is ≈97% of the mean, indicating the
scenario is genuinely bimodal: some seeds the crossing resolves
cleanly for everyone, some seeds it doesn't resolve cleanly for anyone.
On ID switches, **JPDA actually slightly beats MHT** (0.20 vs 0.90 mean
across 20 seeds). The previous entry (seed 113) is left intact for
historical record but the "7× lower OSPA" headline is wrong in
expectation — it was a single favorable realization.

**Methodological lesson.** Scenarios designed to expose an algorithm's
structural advantage need multi-seed validation before any claim is
made. The dropout window in `buildCrossingDropoutScenario` interacts
with the seed-driven position noise in ways that make the crossing
genuinely ambiguous on some draws — and on those draws, deferred
commitment doesn't help because the right answer isn't recoverable
even with hindsight.

**What this changes.** MHT is no longer the codebase's "biggest win."
The infrastructure (TrackTree, N-scan pruning, K_local cap) is still
correctly implemented and architecturally useful, but the demonstrated
empirical advantage over JPDA on this specific scenario doesn't survive
averaging. A scenario where MHT *does* dominate over the multi-seed
average likely exists (e.g., longer dropout vs N_scan, more targets,
explicit identity-preservation metric) but hasn't been found yet.
Recorded as an open follow-up.

### PF on BearingOnlyMovingSensor — direction holds, intervals overlap

| Filter | mean OSPA ± stddev (m) | mean ID switches |
|--------|--------------------------|------------------|
| EKF (CV) | 212.8332 ± 124.6144 | 0.00 |
| UKF (CV) | 214.2199 ± 125.9745 | 0.00 |
| PF       | **180.3379 ± 124.5977** | 0.00 |

The 32% single-seed PF win narrows to ~15% in expectation (212.83 vs
180.34 = 32.49 m gap). The direction is consistent — PF beats both
Kalman variants on every aggregate — but the per-seed variance is so
large (±125 m, ≈70% of mean) that confidence intervals overlap
substantially. Individual seeds can favor either filter; the *average*
favors PF.

The large variance is inherent to bearing-only with a wide range prior:
on some seeds the bearing sequence converges range quickly, on others
it stays in the banana-shaped ambiguity zone for most of the run and
every filter does poorly. 20 seeds is insufficient to tighten this;
N ≥ 100 is the right next step to convert "directionally PF wins" into
"PF beats EKF with 95% confidence."

---

### Honest revised summary of the wins

| Component | Multi-seed status |
|-----------|---------------------|
| UKF | Tied with EKF on every scenario averaged |
| **PF** | **Wins on bearing-only-with-parallax, but ±125 m variance — need more seeds** |
| IMM-2 (free ω) | Tied with EKF (observability gap, expected) |
| **IMM-3 (prescribed ω)** | **Confirmed: 15% OSPA reduction with non-overlapping CIs** |
| **JPDA** | **Confirmed: 75% ID-switch reduction, tightest CIs of any win** |
| ~~MHT~~ | **Retracted: ties JPDA on this scenario; no demonstrated win** |

The codebase has **two confirmed wins** (JPDA, IMM-3), **one
directional win** (PF on parallax bearing-only), and **one retraction**
(MHT). Net: still useful, more honest, less impressive than the
single-seed numbers suggested. JPDA is the clear winner of the
association axis on the scenarios we have today; MHT's added complexity
over JPDA is not yet justified on demonstrated empirical grounds.

---

## Bus-driven confirmation pass (2026-06-02)

Re-ran the four winning comparisons through `SimulatedSensorBus` (full
sensor quartet: OwnShip + AIS + ARPA + EO/IR; ARPA clutter Poisson(5)
per rotation on JPDA and MHT scenarios). Metric: per-window OSPA
(1 s windows, mean of per-window means) + cumulative ID-switch count.
20 seeds (range 201..220, identical to the prior direct-Measurement
sweep). Heading bias deferred to §14.9.

### JPDA vs GNN — bus clutter crossing

| Method | per-window OSPA (m) | mean ID switches |
|--------|---------------------|------------------|
| GNN    | 49.8548 ± 0.0222    | 16.90            |
| JPDA   | 49.8452 ± 0.0274    | **18.55**        |

**Verdict: retracted (under bus).** Prior direct-Measurement win (45.32
vs 47.32 OSPA, 2.45 vs 9.90 ID-switches) does not meaningfully survive.
Both methods saturate near the 50 m OSPA cutoff; JPDA's OSPA edge
(~0.01 m) is well inside one stddev, and it actually **loses on
ID-switches** (18.55 vs 16.90). The prior JPDA advantage came from
clean clutter discrimination on direct Position2D measurements; under
the bus's EO/IR-dominated stream (10 Hz, ~600 measurements per 30 s),
the per-batch clutter exposure is too sparse for JPDA's soft-assignment
machinery to differentiate from GNN's hard nearest-neighbour.

### IMM-3 vs CV — bus maneuvering

| Method | per-window OSPA (m) | mean ID switches |
|--------|---------------------|------------------|
| EKF    | 96.9531 ± 0.4587    | 4.00             |
| IMM-3  | **96.7948 ± 0.3768** | **3.85**        |

**Verdict: directionally preserved, materially diminished.** Prior
direct-Measurement IMM-3 win was 4.81 ± 0.59 vs 5.67 ± 0.91 OSPA
(~15% gap, non-overlapping CIs). Through the bus, IMM-3 still wins on
both metrics but the margin is <1σ (~0.16 m on a ~97 m baseline) — the
prior 15% advantage collapses. Both methods sit near the 100 m OSPA
cutoff, suggesting the 15 s scenario length and the bus's measurement
heterogeneity together prevent IMM from settling into the right mode
before the metric saturates. The direction of the effect is right;
the magnitude no longer matches prior claims.

### PF vs EKF — bus bearing-only moving sensor

| Method | per-window OSPA (m) | mean ID switches |
|--------|---------------------|------------------|
| EKF    | 387.0256 ± 51.5514  | 0.00             |
| PF     | **380.4102 ± 53.6372** | 0.00          |

**Verdict: directional, unchanged from prior.** PF beats EKF on OSPA by
~6.6 m, but the per-seed stddev (~52 m) means CIs overlap heavily —
identical pattern to the prior direct-Measurement sweep (180 ± 125 vs
213 ± 125). The bus version operates at higher absolute OSPA (~380 m vs
~200 m) because the bus EO/IR bearing-only emission has the
projection-time own-ship pose attached via §14.1 — but the ratio is
similar. No new conclusion: PF directionally wins on the high-curvature
bearing-only posterior; N≥100 seeds needed to nail statistical significance.

### MHT vs JPDA — bus clutter crossing

| Method | per-window OSPA (m) | mean ID switches |
|--------|---------------------|------------------|
| JPDA   | 49.8452 ± 0.0274    | **18.55**        |
| MHT    | **49.5934 ± 0.0465** | 25.55           |

**Verdict: retraction re-confirmed.** Prior multi-seed sweep retracted
the MHT win (both ≈ 1.97 m, tied). Under the bus, MHT shows a tiny OSPA
edge (49.59 vs 49.85, ~0.5%) but loses ID-stability by 38% (25.55 vs
18.55). MHT's deferred branching pays for itself only when track
confusion under clutter can be unwound retroactively — here, the bus's
heavy non-ARPA measurement stream (~600 EO/IR detections per 30 s)
already gives JPDA enough info to track correctly without needing
N-scan hypotheses. **Neither dominates; the retraction stands.**

### Cross-cutting observation

Three of four scenarios (JPDA, IMM-3, MHT) show OSPA saturating near
the cutoff — under bus-realistic noise and 20 seeds, the metric loses
discriminative power between methods. This is itself a finding:

- The prior direct-Measurement scenarios (where each scan was 2 clean
  Position2D measurements) gave tracker-quality differences a clear
  signal pathway. The bus's EO/IR-dominated stream (~600 measurements
  per 30 s scenario) overwhelms the per-scan information advantage
  that JPDA's soft assignment / MHT's deferred branching were
  designed to exploit.
- Likely follow-ups: (a) revisit tracker init/delete and gate
  parameters for bus-regime measurement densities, (b) report
  per-window OSPA *conditioned on at-least-one-track-confirmed* so
  the cardinality-penalty saturation doesn't dominate the signal,
  (c) longer scenario durations for IMM-3 to give the mode-switching
  enough time to express.

The bus pass surfaces these limits honestly rather than burying them
behind tuned parameters chasing the direct-Measurement baselines.

### Methodology notes

- Per-window OSPA differs in scale from the prior per-measurement mean
  OSPA because the bus emits ~10× more measurements than direct-
  Measurement scenarios, and 1 s windows average each tick once. Direct
  comparison of *absolute numbers* between this table and the prior
  table is illustrative, not strict; the comparison that matters is
  between methods on the SAME row of each sub-table.
- Bus injects: 1 Hz OwnShip GPS (no heading bias yet), Class-A SOTDMA
  AIS, 3 s ARPA rotation (with optional Poisson clutter), 10 Hz EO/IR
  with bearing+range or bearing-only.
- Determinism: each seed produces a byte-identical Scenario; re-running
  this table yields the same numbers.
- Tests live at `tests/sim/test_bus_jpda_comparison.cpp`,
  `tests/sim/test_bus_imm3_comparison.cpp`,
  `tests/sim/test_bus_pf_comparison.cpp`,
  `tests/sim/test_bus_mht_comparison.cpp`.

## Post-metric-fix bus pass (2026-06-02)

The "Bus-driven confirmation pass" section above was contaminated by a metric
artifact: `runScenario` / `runScenarioBatched` / `runScenarioBatchedMht`
evaluated OSPA *per measurement* and matched truth by `==` on timestamps.
With truth at 1 Hz and EO/IR at 10 Hz, ~93% of evaluation points had empty
`truth_xy`, and `ospaGreedy([], est, cutoff)` returns exactly the cutoff for
any non-empty track set — pinning the reported mean near saturation. See
`docs/superpowers/plans/2026-06-02-truth-tick-ospa.md` for the fix (drive
OSPA evaluation on the truth-sample clock).

### Saturation evidence (seed=201)

| Scenario | Pre-fix empty-truth % | Pre-fix overall OSPA | Post-fix overall OSPA |
|---|---|---|---|
| JPDA clutter crossing (cutoff 50 m)   | 93.1% | 49.88 | 48.26 |
| IMM-3 maneuvering (cutoff 100 m)      | 92.4% | 98.00 | 81.33 |
| PF bearing-only (cutoff 500 m)        |  0.0% | 329.46 | 329.46 |

PF was untouched because that scenario already configures EO/IR at 1 Hz,
matching the truth sample rate.

### Re-run verdicts (20 seeds, post-fix metric)

#### JPDA vs GNN — clutter crossing (cutoff 50)

| Algorithm | Per-window OSPA mean ± σ | ID switches mean |
|---|---|---|
| GNN  | 48.27 ± 0.29 | 20.40 |
| JPDA | 48.15 ± 0.35 | 24.20 |

OSPA margin 0.12 m sits well within seed stddev (~0.3 m) — statistically a
tie. GNN wins ID-stability by ~4 switches/30 s on average. **The
direct-measurement JPDA win remains retracted under bus-realistic noise.**
The pre-fix verdict was correct in direction but masked the magnitude: the
metric was already at 49.85 (cutoff 50) so neither method had room to express
itself; now both are 1.5 m below cutoff with a real but tiny gap.

#### IMM-3 vs CV — maneuvering (cutoff 100)

| Algorithm | Per-window OSPA mean ± σ | ID switches mean |
|---|---|---|
| CV (EKF)   | 76.57 ± 3.47 | 5.55 |
| IMM-3      | 75.51 ± 3.14 | 5.05 |

Direction preserved but the 1.07-m margin is within 1σ. **The direct-measurement
IMM-3 win is meaningfully diminished**: at 15 s scenario length with the bus's
plentiful position fixes (AIS 2 s, ARPA 3 s, EO/IR 10 Hz), the CV-only
estimator stays close enough to truth that IMM's mode-switching advantage
doesn't dominate. Likely needs longer scenarios with sustained maneuvering to
re-express.

#### PF vs EKF — bearing-only moving sensor (cutoff 500)

| Algorithm | Per-window OSPA mean ± σ | ID switches mean |
|---|---|---|
| EKF | 387.03 ± 51.55 | 0.00 |
| PF  | 380.41 ± 53.64 | 0.00 |

**Numerically identical to pre-fix** (as predicted): this scenario configures
EO/IR at 1 Hz with truth at 1 Hz, so no cadence mismatch → no saturation. The
prior verdict stands: directional PF advantage, CIs overlap, PF is not a
clearly justified choice for bearing-only in this regime.

#### MHT vs JPDA — clutter crossing (cutoff 50)

| Algorithm | Per-window OSPA mean ± σ | ID switches mean |
|---|---|---|
| JPDA | 48.15 ± 0.35 | 24.20 |
| MHT  | 45.09 ± 0.60 | 32.60 |

This is the most interesting reveal: under the pre-fix saturated metric MHT
was tied with JPDA at the cutoff. Under the corrected metric MHT shows a real
OSPA margin (~3 m, outside seed stddev), but pays ~35% more ID switches.
**Verdict: trade-off, not a clear winner** — MHT's deferred branch resolution
yields better positional accuracy by re-binding measurements once enough
evidence accumulates, but the cost is more aggressive track ID churn.
Downstream consumers that care about identity continuity (CPA, sensor
hand-off) may still prefer JPDA; consumers that care about positional
accuracy may prefer MHT. The decision is application-dependent rather than
algorithmic.

### Cross-cutting

Three of four prior verdicts (JPDA, IMM-3, MHT) were either reversed or
materially diminished. The metric artifact is responsible for the three
retractions in the pre-fix table appearing more uniform than they should
have. With the corrected metric:

- One verdict held outright (PF — directional only).
- One was meaningfully weakened (IMM-3 — within 1σ).
- One was confirmed-retracted but for the right reason now (JPDA — GNN
  matches on OSPA and beats on ID-stability).
- One revealed a genuine accuracy-vs-stability trade-off (MHT — better OSPA
  at the cost of ID churn).

The general lesson: when evaluating a fusion stack, **the temporal alignment
between truth sampling and metric evaluation has to match** — otherwise
sensors that fire faster than truth ticks contribute cardinality-penalty
noise rather than signal. The truth-tick clock is the standard convention
in the OSPA literature and matches the cadence at which real ground-truth
(GPS) is typically available; we should not have used the per-measurement
clock in the first place.

## Heading error sweep (2026-06-02)

§14.9 wired end-to-end. Own-ship HDT now carries injected bias / drift /
white noise; `ArpaAdapter` and `EoIrAdapter` accept a `heading_std_deg`
that propagates through `projectRangeBearingToEnu` into the bearing
variance (combined in quadrature with the sensor's intrinsic σ).

Sweep: EKF + GNN, 20 seeds (201..220), σ_h ∈ {0°, 0.5°, 1°, 2°},
R-inflation off vs on. Three scenarios re-used from the bus comparison
helpers.

### ClutterCrossing (targets at ~200 m range)

```
[Bus Heading Sweep on ClutterCrossing, 20 seeds]
  sigma_h_deg | R_inflate | per-window OSPA mean   | id_sw_mean
        0.00  | off       | 48.2740 +/- 0.2852 m | 20.40
        0.00  | on        | 48.2740 +/- 0.2852 m | 20.40
        0.50  | off       | 48.2445 +/- 0.2891 m | 20.60
        0.50  | on        | 48.1917 +/- 0.3046 m | 17.90
        1.00  | off       | 48.2469 +/- 0.3038 m | 20.60
        1.00  | on        | 48.1492 +/- 0.3313 m | 16.40
        2.00  | off       | 48.2896 +/- 0.2940 m | 19.60
        2.00  | on        | 48.1067 +/- 0.3379 m | 12.05
```

### BearingOnlyMoving (target at 1.5 km range — headline)

```
[Bus Heading Sweep on BearingOnlyMoving, 20 seeds]
  sigma_h_deg | R_inflate | per-window OSPA mean   | id_sw_mean
        0.00  | off       | 387.5510 +/- 51.4886 m | 0.00
        0.00  | on        | 387.5510 +/- 51.4886 m | 0.00
        0.50  | off       | 419.0032 +/- 47.6722 m | 0.00
        0.50  | on        | 397.6000 +/- 51.9899 m | 0.00
        1.00  | off       | 457.0521 +/- 32.7441 m | 0.00
        1.00  | on        | 402.9367 +/- 52.3337 m | 0.00
        2.00  | off       | 482.6076 +/- 12.0074 m | 0.00
        2.00  | on        | 408.8005 +/- 47.1020 m | 0.00
```

### Maneuvering (single target, 15 s scenario)

```
[Bus Heading Sweep on Maneuvering, 20 seeds]
  sigma_h_deg | R_inflate | per-window OSPA mean   | id_sw_mean
        0.00  | off       | 81.6523 +/- 2.0179 m | 6.15
        0.00  | on        | 81.6523 +/- 2.0179 m | 6.15
        0.50  | off       | 81.0586 +/- 2.2462 m | 6.55
        0.50  | on        | 79.5049 +/- 2.8731 m | 5.55
        1.00  | off       | 81.1884 +/- 2.4011 m | 6.60
        1.00  | on        | 77.5293 +/- 4.0335 m | 4.90
        2.00  | off       | 81.0962 +/- 2.3672 m | 6.55
        2.00  | on        | 74.5369 +/- 4.9032 m | 3.45
```

### Bias / drift propagation probe

Single-seed probe to confirm bias and drift propagate. Plan called for
1° bias / 0.01 deg/s drift; bumped to 3° / 0.03 deg/s after the smaller
magnitudes were too close to the single-seed noise floor on the
1.5 km bearing-only scenario.

```
[Bus Heading Probe: BearingOnlyMoving, seed=201]
  no error   : per-window OSPA mean = 329.4629 m
  bias 3 deg : per-window OSPA mean = 333.5720 m

[Bus Heading Probe: BearingOnlyMoving, seed=201]
  no error     : per-window OSPA mean = 329.4629 m
  drift 0.03/s : per-window OSPA mean = 329.7823 m
```

### Verdict

The BearingOnlyMoving scenario (1.5 km range) is the headline result and
shows the §14.9 failure mode sharply: with R-inflation off, per-window
OSPA climbs monotonically with σ_h (387.55 → 419.00 → 457.05 → 482.61 m),
while R-on stays nearly flat (387.55 → 397.60 → 402.94 → 408.80 m),
recovering roughly 74 m of the ~95 m saturation cliff at σ_h = 2°. This
is exactly the "tracker over-trusts long-range relative bearings when
heading is uncertain" pathology the spec predicted. Maneuvering shows a
smaller but consistent effect: OSPA R-off is flat at ~81 m across σ_h
while R-on drops to 74.5 m at σ_h = 2°, and the ID-switch signal is
cleaner still — R-off ~6.5 across the sweep, R-on falling 6.15 → 5.55 →
4.90 → 3.45 as σ_h grows, indicating R-inflation calms data-association
overreactions. ClutterCrossing (200 m range) shows the expected weak
OSPA response — differences sit below the ~0.2 m stddev noise floor —
but ID-switches still drop materially under R-on (20.40 → 17.90 → 16.40
→ 12.05), so even at short range a heading-aware R reshapes which
scan-to-track associations win. The single-seed bias/drift probe
confirms both error modes propagate end-to-end (drift contributes
~0.3 m of OSPA over a 60 s window at 0.03 deg/s, i.e. a 1.8° final
offset). The overall pattern matches the `range × σ_h` rule the spec
called out: R-inflation is essentially free at small σ_h (the increment
is dominated by intrinsic sensor noise) and progressively saves the
tracker as σ_h grows, with the dramatic gains at long range. Practical
implication: maritime trackers consuming relative bearings should
accept a `heading_std_deg` configuration and propagate it through their
projections — this work makes that path real in navtracker.

### Methodology notes

- Per-window OSPA at 1 s windows (truth-tick clock).
- Heading noise is white (per-tick i.i.d. Gaussian). No process model.
- Bias and drift held at 0 during the sweep; they get a separate probe.
- Sweep uses one canonical tracker per scenario (EKF + GNN). The
  comparison vs other estimators / associators is intentionally not
  re-run; the question here is the error model, not the algorithm.
- Determinism: each seed produces a byte-identical Scenario.
- Tests live at `tests/sim/test_bus_heading_sweep.cpp` and
  `tests/sim/test_bus_heading_bias_drift_probe.cpp`.

## Heading bias estimator (2026-06-03)

**Setup.** Re-runs the §14.9 heading sweep with a global scalar
heading-bias state that the tracker estimates from AIS-vs-ARPA position
residuals on fused tracks. ClutterCrossing's and Maneuvering's primary
target already carries AIS+ARPA+EOIR, so pair observations flow as soon
as a track is confirmed; BearingOnlyMoving has no AIS or ARPA in scene
(EOIR-only), so the estimator never publishes — that row directly tests
the graceful-fallback path. Three rows per σ_h cell: (R-off, no
estimator), (R-on, no estimator), (R-on + estimator). 20 seeds
(201..220), EKF + GNN, publish-variance threshold relaxed to (0.5°)²
so the estimator publishes within the short scenarios. SUCCEED-only
data capture.

### ClutterCrossing — 20 seeds

| σ_h | row        | OSPA mean ± stddev (m) | id_sw_mean |
|-----|------------|------------------------|------------|
| 0.0° | R-off      | 48.27 ± 0.29           | 20.40      |
| 0.0° | R-on       | 48.27 ± 0.29           | 20.40      |
| 0.0° | R-on + est | 47.88 ± 0.48           | **17.85**  |
| 0.5° | R-off      | 48.24 ± 0.29           | 20.60      |
| 0.5° | R-on       | 48.19 ± 0.30           | 17.90      |
| 0.5° | R-on + est | 47.76 ± 0.56           | **14.90**  |
| 1.0° | R-off      | 48.25 ± 0.30           | 20.60      |
| 1.0° | R-on       | 48.15 ± 0.33           | 16.40      |
| 1.0° | R-on + est | 47.65 ± 0.61           | **10.40**  |
| 2.0° | R-off      | 48.29 ± 0.29           | 19.60      |
| 2.0° | R-on       | 48.11 ± 0.34           | 12.05      |
| 2.0° | R-on + est | **47.57 ± 0.62**       | **7.65**   |

### BearingOnlyMoving — 20 seeds (no AIS / no ARPA in scene)

| σ_h | row        | OSPA mean ± stddev (m) | id_sw_mean |
|-----|------------|------------------------|------------|
| 0.0° | R-off      | 387.55 ± 51.49         | 0.00       |
| 0.0° | R-on       | 387.55 ± 51.49         | 0.00       |
| 0.0° | R-on + est | 387.55 ± 51.49         | 0.00       |
| 0.5° | R-off      | 419.00 ± 47.67         | 0.00       |
| 0.5° | R-on       | 397.60 ± 51.99         | 0.00       |
| 0.5° | R-on + est | 397.60 ± 51.99         | 0.00       |
| 1.0° | R-off      | 457.05 ± 32.74         | 0.00       |
| 1.0° | R-on       | 402.94 ± 52.33         | 0.00       |
| 1.0° | R-on + est | 402.94 ± 52.33         | 0.00       |
| 2.0° | R-off      | 482.61 ± 12.01         | 0.00       |
| 2.0° | R-on       | 408.80 ± 47.10         | 0.00       |
| 2.0° | R-on + est | 408.80 ± 47.10         | 0.00       |

R-on+est is byte-identical to R-on across the cell: no AIS+ARPA pairs
get extracted, so the estimator's variance never falls below the
publish threshold and gating stays closed. This is the designed
behavior, not a bug — the R-inflation budget continues to do all the
work in non-cooperative scenes.

### Maneuvering — 20 seeds

| σ_h | row        | OSPA mean ± stddev (m) | id_sw_mean |
|-----|------------|------------------------|------------|
| 0.0° | R-off      | 81.65 ± 2.02           | 6.15       |
| 0.0° | R-on       | 81.65 ± 2.02           | 6.15       |
| 0.0° | R-on + est | 81.66 ± 1.95           | 6.25       |
| 0.5° | R-off      | 81.06 ± 2.25           | 6.55       |
| 0.5° | R-on       | 79.50 ± 2.87           | 5.55       |
| 0.5° | R-on + est | 79.37 ± 2.90           | 5.30       |
| 1.0° | R-off      | 81.19 ± 2.40           | 6.60       |
| 1.0° | R-on       | 77.53 ± 4.03           | 4.90       |
| 1.0° | R-on + est | 77.54 ± 4.03           | 4.90       |
| 2.0° | R-off      | 81.10 ± 2.37           | 6.55       |
| 2.0° | R-on       | 74.54 ± 4.90           | 3.45       |
| 2.0° | R-on + est | 74.51 ± 4.92           | 3.60       |

### Anchor-loss scenario (single seed 401, 120 s)

ClutterCrossing-style scene with σ_h = 2°, R-inflation on, estimator
on. AIS broadcasts on target 1 for [0, 60) s and drops out at t = 60 s.

- `is_published` at t ∈ [30, 60): **true** (estimator converged on
  AIS+ARPA pairs; final variance ≈ (0.29°)²).
- `is_published` at t = 90 s (30 s after dropout): **false** (stale
  window closed; adapters revert to b̂ = 0 with R-inflation only).
- Pre-dropout mean per-window OSPA on [40, 60): 14.17 m.
- Post-dropout mean per-window OSPA on [60, 120): 30.59 m. Growth is
  dominated by target 1's increasing range (cross-track error scales
  with range) and is structurally unrelated to the dropout; the
  bounded-fallback assertion confirms OSPA stays well below the
  cutoff with no divergence.

### Verdict

The bias estimator delivers a clean, measurable ID-stability win in
the AIS-cooperative scene and reverts cleanly when the AIS anchor
disappears. The largest effect is on ClutterCrossing's `id_sw_mean`:
at σ_h = 2°, R-inflation already cut switches 19.6 → 12.05; the
estimator drops them further to **7.65** — a 60% total reduction vs
the no-mitigation baseline. OSPA improvement on the same cell is
smaller (48.11 → 47.57 m) because ClutterCrossing's targets sit at
~200 m where the `range × σ_h` penalty is modest — the ID benefit
comes from sharper, less-uncertain bearings making data-association
decisions more confident under clutter. Maneuvering and
BearingOnlyMoving see no closed-loop OSPA change: Maneuvering's 15 s
duration leaves the estimator barely above the publish threshold, and
BearingOnlyMoving has no AIS in scene so the estimator stays
unpublished by design. Anchor-loss confirms the gating contract — the
30 s stale window closes cleanly, behavior falls back to the §14.9
R-inflation path, and there is no accuracy cliff at the dropout
moment. Practical implication: AIS-vs-ARPA bias estimation is most
valuable in cluttered cooperative scenes where ID stability matters
most; the deferred multi-track bearing-innovation observer (spec
§11 #1) remains the right next step for non-cooperative scenes like
BearingOnlyMoving.

### Methodology notes

- Three sweep TESTs and one anchor-loss TEST: `tests/sim/test_bus_bias_estimator_sweep.cpp`, `tests/sim/test_bus_anchor_loss.cpp`.
- Bus driven via `sim::SimulatedSensorBus::stepOnce(...)` for the estimator-on rows so adapter projections see the latest published b̂ on the cycle after each AIS+ARPA pair is observed.
- Publish threshold (0.5°)² for the sweep; default (0.3°)² used elsewhere.
- AIS dropout in the anchor-loss test uses `sim::AisEmitterConfig::dropout_windows_s`.
- Default `AisArpaPairExtractorConfig` (cycle window 0.5 s, AIS σ fallback 10 m, ARPA bearing σ fallback 1°).
- The estimator is intentionally bias-agnostic during sim warmup — initial state b̂ = 0, variance (5°)². No precomputed calibration.

## GPS position uncertainty (2026-06-03)

**Setup.** Sim injects own-ship GPS position noise via
`sim::OwnShipEmitterConfig::gps_pos_std_m` (zero-mean Gaussian on lat/lon
each tick). When `report_gps_std` is true the emitter advertises
`σ_GPS` on the published `OwnShipPose`, and `ArpaAdapter`/`EoIrAdapter`
inflate projected covariance by `σ²_GPS · I` (the R-on row). When false
the same noise corrupts the projection origin but the adapter is blind
to the budget (R-off row — apples-to-apples noise, unmodeled).
EKF + GNN, 20 seeds (201..220), σ_GPS ∈ {0, 0.1, 1, 5} m.

### ClutterCrossing (close range, ~200 m)

```
[Bus GPS Sweep on ClutterCrossing, 20 seeds]
  sigma_gps_m | R_inflate | per-window OSPA mean   | id_sw_mean
        0.00  | off       | 48.6067 +/- 0.2158 m | 10.20
        0.00  | on        | 48.6067 +/- 0.2158 m | 10.20
        0.10  | off       | 48.6073 +/- 0.2141 m |  9.85
        0.10  | on        | 48.6064 +/- 0.2149 m |  9.05
        1.00  | off       | 48.6122 +/- 0.2163 m | 14.80
        1.00  | on        | 48.6087 +/- 0.2145 m |  9.05
        5.00  | off       | 48.7099 +/- 0.2069 m | 21.40
        5.00  | on        | 48.6223 +/- 0.2150 m |  7.75
```

### BearingOnlyMoving (long range, ~1500 m, sanity probe)

```
[Bus GPS Sweep on BearingOnlyMoving, 20 seeds]
  sigma_gps_m | R_inflate | per-window OSPA mean   | id_sw_mean
        0.00  | off       | 388.8522 +/- 49.0193 m | 0.00
        0.00  | on        | 388.8522 +/- 49.0193 m | 0.00
        0.10  | off       | 388.8307 +/- 49.0620 m | 0.00
        0.10  | on        | 388.8292 +/- 49.0622 m | 0.00
        1.00  | off       | 388.6445 +/- 49.4416 m | 0.00
        1.00  | on        | 388.5005 +/- 49.4561 m | 0.00
        5.00  | off       | 387.5510 +/- 51.4886 m | 0.00
        5.00  | on        | 384.0360 +/- 51.8883 m | 0.00
```

### Verdict

At close range (ClutterCrossing, targets ~200 m), the R-on inflation
materially improves ID stability as σ_GPS grows: at σ_GPS = 5 m the
mean id-switch count drops from 21.40 (R-off) to 7.75 (R-on) — a ~64%
reduction — while OSPA is essentially unchanged (positional accuracy
is dominated by the bearing/range terms even before GPS noise). The
mechanism is the same as §14.9's heading-R-inflation: a better-budgeted
R gate keeps the GNN from chasing clutter that the unmodeled GPS
wobble has dragged into the gate. At long range (BearingOnlyMoving,
target ~1500 m), the σ_GPS = 5 m R-on vs R-off OSPA delta is in the
single-seed noise (~3.5 m on a ~388 m baseline with stddev ~50 m) —
exactly the inverse-of-heading gradient predicted by the spec:
GPS uncertainty is a position-frame additive σ² that doesn't scale
with range, so its relative impact shrinks as the target moves away,
while heading uncertainty rotates the whole bearing arm and grows
linearly with range. Together with §14.9 (heading R-inflation, close
range wins on ID; long range wins on OSPA) and the heading bias
estimator (2026-06-03; closes the loop on slowly-varying mean offset),
the GPS-uncertainty budget completes the own-ship error pipeline for
the cooperative tracker.

### Methodology notes

- One sweep TEST per scenario: `tests/sim/test_bus_gps_sweep.cpp`.
- Same R-on/off comparison protocol as the heading sweep: noise is
  always injected; only the advertised `pose.position_std_m` toggles.
- ClutterCrossing uses `clutter_per_rotation = 8`; BearingOnlyMoving is
  EOIR-only and still picks up `σ_GPS` through `projectRangeBearingToEnu`
  when R-on.

## Adaptive UERE (2026-06-03)

**Setup.** Online σ_pos estimator runs over GGA-derived local-meter
positions in a sliding 8-sample window (`core/own_ship/UereEstimator`).
The estimator does a least-squares constant-velocity fit on each axis
and uses the residual variance as a direct σ_pos estimate. A two-halves
velocity check (|Δv| > 0.5 m/s) suppresses publication during maneuvers
so transient kinematics do not pollute the noise estimate. When the
estimator publishes, its σ overrides the static `HDOP × UERE` path in
`OwnShipNmeaAdapter`; otherwise the static path applies. Adaptive mode
is default off; sweep tests opt in via
`OwnShipNmeaAdapterConfig::enable_adaptive_uere = true` and turn the
sticky sim-side setter off (`report_gps_std = false`) so the estimator
must observe the noise it then advertises.

### Tracking σ across injected levels (ClutterCrossing, 20 seeds)

Stationary own-ship; `OwnShipEmitter` injects N(0, σ_inj²) lat/lon noise
on each GGA fix; bus runs 30 s → ~30 GGA fixes; we read the provider's
`position_std_m` at end-of-run as the estimator's most recent verdict.

| sigma_injected (m) | mean published sigma (m) | within ±50%? |
|---|---|---|
| 0.10 | 0.0910 | yes |
| 1.00 | 0.9158 | yes |
| 5.00 | 4.5777 | yes |

### Sweep comparison (ClutterCrossing, 20 seeds, EKF + GNN)

Same scenario as G8's `BusGpsSweep.ClutterCrossing`. Three rows per σ
cell: R-off (no inflation), R-on static (HDOP×UERE via sticky setter,
adaptive off), R-on adaptive (estimator publishes, sticky off).

| sigma_gps | row             | per-window OSPA       | id_sw |
|-----------|-----------------|-----------------------|-------|
| 0.00      | R-off           | 48.6067 ± 0.2158      | 10.20 |
| 0.00      | R-on static     | 48.6067 ± 0.2158      | 10.20 |
| 0.00      | R-on adaptive   | 48.6063 ± 0.2159      |  9.90 |
| 0.10      | R-off           | 48.6073 ± 0.2141      |  9.85 |
| 0.10      | R-on static     | 48.6064 ± 0.2149      |  9.05 |
| 0.10      | R-on adaptive   | 48.6072 ± 0.2147      |  9.05 |
| 1.00      | R-off           | 48.6122 ± 0.2163      | 14.80 |
| 1.00      | R-on static     | 48.6087 ± 0.2145      |  9.05 |
| 1.00      | R-on adaptive   | 48.6075 ± 0.2152      | 10.20 |
| 5.00      | R-off           | 48.7099 ± 0.2069      | 21.40 |
| 5.00      | R-on static     | 48.6223 ± 0.2150      |  7.75 |
| 5.00      | R-on adaptive   | 48.6750 ± 0.2172      | 12.05 |

### Verdict

The estimator tracks the injected σ within ±50 % across two decades
(0.1 → 5 m), confirming the sliding-window residual-variance design as a
viable online observer of own-ship GPS noise. In the bus sweep, the
adaptive R-on row matches the static R-on row in OSPA to within
statistical noise at all four σ levels (mean OSPA spreads of < 0.06 m
across rows), and recovers most of static's id-switch advantage at
moderate σ (≤ 1 m). At σ = 5 m, adaptive's id-switch count is slightly
worse than static (12.05 vs 7.75) — expected, since static is
calibrated to truth while adaptive must estimate σ from 8 samples per
window, and σ̂ is undershooting truth by ~10 % on average. Adaptive's
value here is not numerical improvement (it cannot beat a path that
already knows the answer) but elimination of the static UERE knob:
deployment scenarios where σ is not known a priori (degraded GNSS,
multipath, RAIM-without-augmentation) now have a closed-loop story
analogous to the heading bias estimator (2026-06-03) on the heading side.

### Methodology notes

- Two TESTs in `tests/sim/test_bus_adaptive_uere.cpp`:
  `AdaptiveTracksSimInjectedSigma` (asserts ±50 % tracking, EXPECT_GE/LE)
  and `AdaptiveSweepClutterCrossing` (SUCCEED-only sweep, prints the table).
- The sweep reuses `runBusClutterCrossingWithGps` from
  `tests/sim/BusComparisonHelpers.hpp` with a new `adaptive_uere` flag on
  `GpsSweepKnob`; default false preserves all pre-existing sweeps and
  matches the byte-identical regression contract.
- `OwnShipNmeaAdapter` now leaves `pose.position_std_m` untouched in the
  HDT branch — only GGA messages update position uncertainty. This fixes
  a Task-2-era oversight where an interleaved HDT would clobber the
  adaptive σ between GGA fixes.

## CPA uncertainty (2026-06-03)

**Setup.** Jacobian-based linear propagation of joint track covariance
through the closed-form CPA function. Output: mean and σ on cpa and
tcpa, and P(CPA < d_threshold) under a 1-D Gaussian on CPA. Own-ship is
synthesised as a Track via `synthesizeOwnShipTrack` with σ_pos from the
GPS work; σ_v_own = 0 per v1 decision. Spec:
`docs/superpowers/specs/2026-06-03-cpa-uncertainty-design.md`. Plan:
`docs/superpowers/plans/2026-06-03-cpa-uncertainty.md`.

### Predicted CPA on a known perpendicular-pass

Geometry: own-ship stationary at the ENU origin; target starts at
(0, 1000) m moving east at 10 m/s. Truth CPA = 1000 m (target is at its
closest at t = 0 and only recedes); tracker is driven with 1 Hz
Position2D measurements for 20 s. Predicted CPA evaluated at t_ref =
10 s; alarm threshold = 500 m. Numbers from
`tests/scenario/test_cpa_scenario.cpp`.

| measurement noise (σ_pos_meas) | own-ship σ_pos | predicted CPA (m) | σ_cpa (m) | P(<500 m) | in 2σ band? |
|---|---|---|---|---|---|
| 1 m | 1 m | 1006.722 | 4.2561 | < 1e-6 | yes |
| 1 m | 5 m | 1006.722 | 6.4896 | < 1e-6 | yes |
| 5 m | 1 m | 1003.826 | 5.8069 | < 1e-6 | yes |
| 5 m | 5 m | 1003.826 | 7.5974 | < 1e-6 | yes |

### CPA bands across §14.9 sweep scenarios (20 seeds, R-on, EKF+GNN)

Mean CPA / σ_cpa / P(<200 m) aggregated over every confirmed-target
pair against a synthesised own-ship at the ENU origin (Clutter and
Maneuvering: stationary own-ship; BearingOnlyMoving: own-ship velocity
(0, 10) m/s, matching the sim). Numbers from
`tests/sim/test_bus_cpa_uncertainty.cpp`. d_threshold = 200 m.

| scenario | σ_h | σ_GPS | mean CPA (m) | σ_cpa (m) | P(<200 m) | n pairs |
|---|---|---|---|---|---|---|
| ClutterCrossing | 0° | 0 m | 1939.329 | 742.918 | 0.2116 | 323 |
| ClutterCrossing | 2° | 0 m | 4344.420 | 3574.362 | 0.1832 | 298 |
| ClutterCrossing | 0° | 5 m | 4178.077 | 1690.213 | 0.1193 | 141 |
| Maneuvering | 0° | 0 m |  133.996 |   9.419 | 0.9937 | 119 |
| Maneuvering | 2° | 0 m |  136.433 |   7.202 | 0.9993 |  64 |
| BearingOnlyMoving | 0° | 0 m | 1057.467 | 182.779 | 0.000794 | 20 |
| BearingOnlyMoving | 2° | 0 m | 1062.396 | 190.656 | 0.002076 | 20 |
| BearingOnlyMoving | 0° | 5 m | 1062.478 | 182.593 | 0.000728 | 20 |

(The Maneuvering / σ_GPS = 5 m cell is omitted: the existing harness
provides single-knob helpers only, so the simpler variant from the plan
covers each cell with one knob at a time. The 3 × 3 picture below is
sufficient for the verdict.)

### Verdict

Truth CPA = 1000 m falls inside the 2σ band on the known perpendicular-
pass in every noise cell (σ_cpa is order-of-magnitude small relative to
the 4-7 m deviation between predicted and truth, so the band closes
comfortably). σ_cpa grows monotonically with own-ship σ_pos at fixed
measurement noise (4.26 → 6.49 m) and with measurement noise at fixed
own-ship σ_pos (4.26 → 5.81 m), confirming the joint Jacobian path
faithfully carries both legs of input uncertainty through to the
output. On the §14.9 bus sweeps σ_cpa is materially larger when σ_h is
raised (ClutterCrossing 743 → 3574 m at 0 → 2°) than when σ_GPS is
raised (743 → 1690 m at 0 → 5 m), which lines up with the Task-7/Task-8
heading-bias work being the dominant covariance source in stationary-
own-ship scenarios. P(<200 m) is the operational output: it cleanly
separates the Maneuvering scenario (mean P ≥ 0.99 — the target really
does pass within 200 m) from the recede-only ClutterCrossing /
BearingOnlyMoving scenarios (mean P ≤ 0.21), so a downstream alarm can
threshold on this number directly. The 1-D Gaussian approximation
remains documented for near-collision cases (spec §11).

### Methodology notes

- One assertive scenario test
  (`tests/scenario/test_cpa_scenario.cpp::PerpendicularPassTwoSigmaBandContainsTruth`)
  pins the 2σ-band claim; one SUCCEED-only sweep
  (`PerpendicularPassNoiseSweepReport`) and one bus sweep
  (`tests/sim/test_bus_cpa_uncertainty.cpp::SweepAcrossScenarios`)
  print the tables above.
- The bus sweep uses `runBus*WithHeading` and `runBus*WithGps` helpers
  one knob at a time per cell. Adding a combined-knob helper was
  unnecessary for the verdict.
- For BearingOnlyMoving the own-ship is moving north at 10 m/s in the
  sim; the synthesised own-ship Track for CPA uses the same velocity so
  the geometry is consistent.
- Suite size 286/286 green after this work (+3 over the 283 baseline:
  two `CpaScenario.*` tests plus one `BusCpaUncertainty.*` sweep).

## RMC velocity + CPA σ (2026-06-04)

**Setup.** Closes the v1 simplification σ_v_own = 0 from the CPA spec.
RMC SOG/COG parsing in OwnShipNmeaAdapter, with a GGA-finite-difference
fallback (OwnShipVelocityEstimator) when RMC is absent. The pose now
carries velocity_enu + velocity_std_m_per_s + velocity_is_valid;
synthesizeOwnShipTrack reads them directly; CPA's existing Jacobian
propagates σ_v into σ_cpa.

### Future-CPA perpendicular pass (truth CPA = 1000 m, TCPA = 100 s)

Target at (-1000, 1000) m moving east at 10 m/s; own-ship stationary at
origin. CPA in the future at t = 100 s. d_threshold = 200 m.

| σ_pos (m) | σ_v (m/s) | predicted CPA | σ_cpa  | P(<200m)  |
|-----------|-----------|---------------|--------|-----------|
| 1.0       | 0.0       | 1000.000      | 10.0995| 0.000000  |
| 1.0       | 0.5       | 1000.000      | 51.0098| 0.000000  |
| 1.0       | 1.0       | 1000.000      | 100.5087| 0.000000 |
| 1.0       | 2.0       | 1000.000      | 200.2548| 0.000032 |

### Past-CPA scenario (v1 perpendicular pass)

The original perpendicular-pass test (target at (0, 1000) m moving east
at 10 m/s, t_ref = 10 s) sits in the past-CPA branch — at t_ref the
target has moved east of the closest-approach point, so
computeCpaWithUncertainty falls back to current-distance with σ from
current dp covariance. Velocity uncertainty does not enter the σ_cpa
computation in this branch. Documented limitation; the future-CPA test
above is the one that exercises σ_v propagation.

### Verdict

The future-CPA perpendicular-pass geometry demonstrates the RMC velocity
integration end-to-end. σ_cpa grows strictly with σ_v at fixed TCPA, with
the growth scaling as O(σ_v · TCPA) — at TCPA = 100 s and σ_v = 1 m/s the
contribution to σ_cpa is ~100 m, which is the dominant term when σ_pos = 1 m
(σ_cpa baseline ≈ 10 m). This matches the predicted scaling from the
Jacobian's velocity-uncertainty path. The mean CPA is unchanged by
velocity uncertainty (no bias introduced). P(<200 m) grows accordingly: at
σ_v = 0 the probability is zero (truth is 1000 m away), while at σ_v = 2 m/s
it rises to 3.2 × 10⁻⁵ (the 200-m band now contains tail mass from the
widened σ_cpa). The past-CPA fallback (original perpendicular-pass test)
documented limitation that σ_v does not enter is acceptable for v1 — in
practice, maritime operators care most about future-CPA risk where velocity
uncertainty dominates; when targets are already in the past-CPA zone the
vessel is already closest and risk is determined by current distance, not
velocity derivatives.

### Methodology notes

- Sweep test: `tests/scenario/test_cpa_scenario.cpp::PerpendicularPassVelocityUncertaintySweepReport`.
- Suite size 318/318 green (was 317; +1 new test).

---

## 2026-06-10 — Multi-sensor harness + miss-model fixes; baseline `2026-06-10_multisensor_fixes`

### What changed

Four root-cause fixes from the AutoFerry "why is textbook IMM+TOMHT bad
on real data" review:

1. **Harness (dominant):** the AutoFerry loader unified per-target truth
   timestamps onto one timestamp per scan (per-target skews of ~0.1 s
   were fragmenting every 2-target evaluation step into two 1-target
   steps, pegging OSPA at the 500 m cutoff and producing ~3.2e3 phantom
   id_switches for every config), deduplicated repeated truth scans, and
   derived finite-difference truth velocities. Bench continuity/RMSE
   metrics are now keyed by `truth_id` with time-varying cardinality.
2. **Per-sensor miss model:** TrackTree's miss branch charges
   Σ_s log(1 − P_D^s(x)) over the distinct sensors in each scan,
   coverage-conditioned (lidar max_range 140 m); IPDA's miss recursion
   uses the scan-effective P_D; IPDA/VIMM persistence is a per-second
   rate (π^dt). AutoFerry scenarios declare a per-sensor detection
   table calibrated from ground truth (radar 0.8 / 1e-5 m⁻², lidar
   0.7 / 5e-6 m⁻² / 140 m, EO+IR 0.6 / 0.5 rad⁻¹) replacing the
   dimensionally-wrong scalar λ_C = 1e-2 override.
3. **IMM TPM dt-scaling:** π is the 1 s TPM, predict applies π^dt and
   advances μ to the predicted prior; update consumes it.

### Measured (scenario2, canonical `imm_cv_ct_mht`)

| metric | pre-fix | post-fix |
| --- | --- | --- |
| track_breaks | 608 | 64.5 |
| id_switches | ~2.0e3 (phantom-dominated) | 146 |
| lifetime_ratio | 0.805 (broken metric) | 0.771 |
| pos_rmse_m | 30.3 | 18.4 |

Synthetic scenarios: **bit-identical** for all canonical configs
(verified via `navtracker_bench_compare` — all-zero deltas), confirming
the fixes are exact no-ops at the 1 Hz cadence.

### IPDA / VIMM ablations (first baseline including them)

On every AutoFerry scenario the existence lifecycle dominates M-of-N:
scenario2 breaks 64.5 → 11.5 (IPDA) / 7 (VIMM), lifetime 0.77 → 0.94,
pos_rmse 18.4 → 8.8, OSPA 413 → 379/377 — the best OSPA of any config
including GNN (457), because existence both keeps true tracks alive
through camera-blind stretches and suppresses clutter births. Same
pattern on scenarios 3–22. On synthetic dense_clutter, IPDA/VIMM cut
OSPA 379 → 137/128.

**Open gap:** on clean synthetics (crossing) IPDA/VIMM cost OSPA
(19.7 → ~82, p95 = 500) from confirmation latency at track birth
(r₀ = 0.5 must climb past 0.9) plus occasional mid-run existence dips.
Tuning (lower confirm threshold with hysteresis, higher r₀ in clean
scenes, or score-gated fallback) is the next experiment before making
IPDA/VIMM the canonical lifecycle.

**Known limitation (philos):** all MHT configs remain broken on philos
(lifetime ≤ 0.015; IPDA 0). Philos truth is asynchronous per-vessel AIS
with no scan structure, so the AutoFerry per-scan truth fix does not
apply; it needs time-windowed truth resampling, and its clutter
environment still uses the legacy scalar λ_C. Tracked as follow-up.

### Key insight (IMM on real data)

On AutoFerry, IMM mode probabilities converge to the TPM's stationary
distribution regardless of dt-scaling: CV and CT are indistinguishable
through 2-D position measurements at 16 Hz (ω weakly observable →
per-mode likelihoods nearly equal), so the kinematic output is
insensitive to μ. The dt fix matters where modes actually separate
(turn scenarios at radar-favourable geometry); the AutoFerry lifecycle
churn was never an estimator problem.

### Methodology notes

- Baseline: `docs/baselines/2026-06-10_multisensor_fixes.{csv,md}`;
  diff vs 2026-06-09:
  `docs/baselines/2026-06-09_robust_vs_2026-06-10_multisensor_fixes.md`.
- New regression pins: `tests/benchmark/test_replay_scenario_run.cpp`
  (GNN + MHT sanity on real scenario2),
  `tests/tracking/test_track_tree.cpp` (per-sensor miss scoring,
  dt-scaled existence), `tests/estimation/test_imm_estimator.cpp`
  (π^dt, semigroup), `tests/benchmark/test_metrics.cpp` (truth_id
  keying, time-varying cardinality).
- Suite size 511/511 green.

## 2026-06-11 — IPDA/VIMM becomes the canonical lifecycle

### Changes

1. **Stale-input guard, default ON** (`Tracker` + `MhtTracker`): inputs
   older than the engine's high-water mark are dropped and counted
   (`staleDropped()`); equal timestamps pass. Opt-out for
   guaranteed-ordered feeds. In-order feeds bit-identical.
2. **Default-detection-model diagnostic**:
   `MhtTracker::defaultDetectionModelWarning()` goes sticky-true when
   ≥2 distinct (SensorKind, MeasurementModel) keys run on the
   auto-installed single-default model.
3. **IPDA confirmation hysteresis**: confirm 0.9 / demote 0.6 with an
   ever-confirmed flag on `TrackTree`; once confirmed, a track holds
   Confirmed down to the demote threshold; re-confirmation requires the
   full confirm threshold. `demote == confirm` reproduces the
   memoryless readout exactly.
4. **Honest detection tables for all 10 synthetic scenarios**
   (scenario *properties*, like the calibrated autoferry table):
   P_D 0.95; λ_C = 1e-6 m⁻² floor for the clutter-free scenarios,
   3.33e-5 m⁻² for dense_clutter (4 FA / 600×200 m box), 1e-2 rad⁻¹
   for the bearing-only scenario.
5. **Canonical lifecycle flip**: `use_ipda_lifecycle = use_visibility
   = true` are now the `MhtTracker::Config` defaults and the canonical
   bench config; M-of-N kept as the `imm_cv_ct_mht_mofn` ablation
   (SPRT remains behind its flag).

### Root cause of the old IPDA synthetic latency

Not r₀ or thresholds: clutter-free synthetics scored with the legacy
global λ_C = 1e-4 m⁻². The existence LR for a gated hit is
L = P_D·g(z)/λ_C with g evaluated under the *track's* predicted
density; a young track's diffuse (unconverged) covariance spreads g so
thin that L < 1 — a perfect hit was evidence *against* existence.
Measured on crossing-equivalent feeds: r walks 0.5 → 0.19 over scans
2–4 before the filter converges, confirm at scan 7 ⇒ lifetime 0.875
(two targets × ~6 scans of a 40-step scenario). With the honest
λ = 1e-6 the same feed confirms at scan 2. r₀ stays 0.5 (Musicki):
raising it would emit clutter-born trees as Confirmed for 1–2 scans.

### Measured (2026-06-11_vimm_canonical vs 2026-06-10 IPDA/VIMM rows)

- Clean synthetics (crossing, head_on, overtaking, parallel, dropout
  pair, clock_skew, speed_change): IPDA/VIMM now **bit-identical to
  M-of-N** — with honest tables every lifecycle confirms at scan 2 and
  the lifecycles only diverge where misses are actually processed.
  ais_dropout: 148 → 66 OSPA (existence no longer dies through the
  10 s gap and re-pays birth latency).
- dense_clutter: VIMM 245 vs M-of-N 421 OSPA (M-of-N regressed under
  honest λ — clutter hits score higher, score-deletes get slower —
  while existence handles them; the flip retires that failure mode).
- AutoFerry: VIMM improved again over 2026-06-10 (scenario2 breaks
  11.5/7 → 1.5, lifetime 0.945 → 0.954; scenario17 OSPA 380 → 369;
  scenario22 breaks 11 → 4.5). The residual ~59 id_switches on
  scenario2 are duplicate-tree swaps (backlog §3).
- speed_change canonical 44 → 18 OSPA (honest tables also fixed the
  M-of-N score scale there).

### Methodology notes

- Baseline: `docs/baselines/2026-06-11_vimm_canonical.{csv,md}`;
  config labels: `imm_cv_ct_mht` is now the VIMM lifecycle,
  `imm_cv_ct_mht_mofn` is the old lifecycle, `imm_cv_ct_mht_vimm`
  was removed (duplicate of canonical).
- Pins tightened: scenario2 MHT lifetime > 0.9, breaks < 10,
  switches < 120 (measured 0.954 / 1.5 / 59).
- philos unchanged (needs truth resampling — backlog §7).

### Addendum 2026-06-11 — cross-tree duplicate merge (backlog §3)

New pass in `MhtTracker::processBatch` before the global solve: retire
the younger of two trees whose best leaves stay within a position-block
Bhattacharyya bound (default 1.0) for `duplicate_merge_seconds`
(default 3.0) of sustained stream time; the older external id survives
(ID-stability invariant); the clock resets the moment a pair separates.

**Why time-based.** The first implementation counted 3 consecutive
close *scans* — at AutoFerry's ~16 Hz union rate that is ~0.19 s, and
real vessels passing close merged almost instantly: scenario6 breaks
2.5 → 11.5, scenario4 lifetime 0.99 → 0.89. Same multi-rate lesson as
scan-counted M-of-N confirmation. The time-based rework recovered the
regressions (scenario6 breaks back to 2.5, scenario4 lifetime 0.94)
while keeping most of the duplicate suppression.

**Measured (2026-06-11_crossmerge vs 2026-06-11_vimm_canonical,
canonical config):**

- id_switches roughly halved on every autoferry scenario: sc16
  68.5 → 10, sc17 27 → 9, sc3 62 → 38.5, sc4 36.5 → 21, sc2 59 → 39.5.
- OSPA down on all autoferry scenarios (duplicates were a permanent +1
  cardinality error): sc16 412 → 335, sc17 369 → 289, sc13 397 → 360.
- dense_clutter OSPA 245 → 103 (duplicate clutter trees retired);
  ais_dropout 66 → 55.
- Clean synthetics bit-identical (no false merges; parallel targets,
  crossings unaffected).
- Honest residuals: lifetime −0.02..−0.07 on sc3/sc4/sc17 — pairs of
  real tracks that genuinely stay within the bound ≥ 3 s, typically
  while one coasts under occlusion with an inflating covariance
  (Bhattacharyya widens). FOV/occlusion modelling (backlog §4) and a
  bias-aware merge distance (§9) are the refinements. Remaining
  switches (sc5 ~97) are not duplicate-induced.
- Scenario2 e2e pin tightened: id_switches < 80 (measured 39.5).
- Side effect: scenario2 e2e runtime 14.6 s → 2.6 s (fewer live trees
  → smaller Murty problems).

## 2026-06-11 — Backlog item 4: source-keyed detection entries, FOV sectors, EO/IR split

**Change.** `ISensorDetectionModel` gained a source-aware lookup
(`paramsFor(sensor, model, source_id)`, fallback source-exact →
kind-wide → defaults) and `DetectionParams` gained azimuth-sector
coverage (`sector_center_rad`/`sector_width_rad`, ENU math convention,
default full circle; evaluated in `missDetectionProbability` alongside
`max_range_m` — out-of-sector tracks charge no miss penalty). The
TrackTree miss loop now keys distinct surveying sensors by the full
(sensor, model, source) triple, so EO and IR cameras sharing
`SensorKind::EoIr` each charge their own calibrated miss penalty.
AutoFerry declares split camera entries; bench plumbing carries an
optional `source_id` per `SensorDetectionEntry`.

**Calibration (per camera, 0.15 rad gate, all nine ground-truthed
scenarios).** EO P_D 0.73 aggregate (0.62–0.87), IR 0.46 (0.21–0.57);
per environment: open water (sc2–6) EO 0.7 / IR 0.5, urban channel
(sc13/16/17/22) EO 0.8 / IR 0.4. Unmatched-bearing rate: open water
0.004–0.6 rad⁻¹, urban 1.0–4.9 rad⁻¹.

**Negative result worth keeping: the measured urban λ must NOT be fed
into the uniform-λ score.** First sweep
(`2026-06-11_eoir_split_measured_lambda`) used the honestly-fitted
per-environment λ and collapsed urban lifetime: sc17 0.65 → 0.35, sc13
0.77 → 0.59, sc22 0.71 → 0.44. The urban excess is persistent
structured shoreline/moored-vessel returns, not uniform Poisson
clutter; the ML-fitted parameter of a wrong model family is not the
right operating point (each camera hit — including on true targets —
was charged ~2 extra nats). Camera λ stays at the kind-wide 0.5 rad⁻¹,
regression-pinned in
`ReplayScenarioRun.AutoferryDeclaresSplitEoIrDetectionEntries`, until
the spatial clutter map (backlog §5) models the shoreline.

**Measured (2026-06-11_eoir_split vs 2026-06-11_crossmerge, canonical
config, P_D split only).**

- lifetime_ratio up on ALL nine autoferry scenarios: sc17
  0.647 → 0.902, sc22 0.706 → 0.837, sc16 0.791 → 0.851, sc3
  0.85 → 0.872, sc5 0.899 → 0.913. track_breaks down or flat
  everywhere except sc6 (+0.5).
- Honest IR P_D (0.4 vs the combined 0.6) is the driver: IR misses —
  which dominate the 16 Hz stream — now charge a miss penalty that
  matches how often the IR camera actually detects, so tracks survive
  IR-dark stretches instead of dying.
- Coverage-vs-accuracy trade, recorded honestly: tracks that now
  survive obscuration coast through it, so urban id_switches rise from
  very low bases (sc17 9 → 23, sc22 10 → 24) and coasting pos_rmse
  climbs (sc17 17.9 → 36.3). OSPA mixed (sc13 360 → 348 and sc17 p95
  500 → 447 improve; sc2/16/22 mean worsens ≤ 43). The OSPA cost is
  the price of reporting tracks through occlusion instead of dropping
  them; FOV/occlusion-aware coasting (now backlog §5/§11 follow-ups)
  is the refinement.
- sc5 id_switches 97.5 → 91: marginal, as predicted — diagnosed
  separately (see below). Clean synthetics, dense_clutter, philos:
  bit-identical (no source-keyed entries there).
- Scenario2 e2e pins re-verified: lifetime 0.958, breaks 1.5,
  switches 37.5 (pins 0.9 / 10 / 80).

**Scenario5 root cause (new backlog §11).** The ~91 residual switches
are bearing-driven identity churn: the two vessels are never closer
than 44 m, but sit < 0.15 rad apart as seen from ownship for 36% of
the 139 s run (< 0.1 rad for 20%) while cameras provide 2891 of 3250
scans and radar refreshes ~0.6 Hz. Bearings gate into both tracks and
the global hypothesis swaps them; the slow radar cannot re-anchor
identity. Neither a duplicate-tree nor a close-pass problem —
candidate fixes recorded in backlog §11.

## 2026-06-11 — Backlog item 7: philos asynchronous truth resampling

**Change.** `resampleTruthToClock` (`core/scenario/TruthResample.hpp`):
linear interpolation of each vessel's asynchronous AIS-as-truth track
onto a shared fixed evaluation clock (segment-FD velocities,
nearest-tick snap at span endpoints so single-fix vessels get one-step
presence, max-gap guard against bridging real dropouts).
PhilosScenarioRun resamples at 1 Hz / 30 s and declares a calibrated
per-sensor detection table: radar P_D 0.07 / λ 2.7e-6 m⁻² / 1000 m
coverage **per sub-scan event** (the rotating sweep arrives as ~10
narrow azimuth bursts per second; measured across 187 vessel × event
opportunities at a 30 m gate), AIS P_D 0.05 / λ 1e-9 (a broadcast
"detects" one vessel per event → per-event P_D ≈ 1/N_vessels).

**Why.** Philos truth carries no scan structure: no two raw samples
share a timestamp, so BenchRunner's exact-time bucketing fragmented
every evaluation step to cardinality 1 — the same harness failure mode
as the pre-fix AutoFerry truth, in its asynchronous form. All MHT
configs scored lifetime ≤ 0.015 with OSPA pegged at the cutoff, and
GNN/JPDA scores were *flattered* (per-vessel presence collapsed to its
2–5 raw message instants, trivially covered).

**Measured (2026-06-11_philos_resample vs 2026-06-11_eoir_split;
philos only — every other scenario bit-identical).**

- Canonical imm_cv_ct_mht: lifetime 0 → 0.295, OSPA 500 → 430, breaks
  0.04, switches 0.17, pos_rmse 38 m. All IPDA/VIMM MHT configs land
  in the same band (0.27–0.30 lifetime, 428–432 OSPA).
- GNN/JPDA lifetime drops 0.68 → 0.33–0.35: the old value was an
  artifact of fragmented presence; the new one is honest and now
  comparable across configs.
- M-of-N ablation (imm_cv_ct_mht_mofn) stays at lifetime ≈ 0.01 — it
  cannot confirm on a ~10 s AIS cadence interleaved with ~10 Hz radar
  events; per-dataset evidence for why the IPDA lifecycle is canonical.
- The remaining lifetime ceiling (~0.3) is honest confirmation latency
  on a ~20 s fixture where most vessels carry only two AIS fixes ~10 s
  apart: confirmed-from-second-fix costs half such a vessel's presence
  window. A longer philos capture would raise it mechanically.
- Pins: `ReplayScenarioRun.PhilosResampledTruthAndMhtLifecycle`
  (cardinality ≥ 10 at peak, lifetime > 0.2, breaks < 2, switches < 5,
  OSPA < 470, rmse < 60).

Boston-harbor caveat, recorded for item 5: most unmatched radar plots
are persistent shore/moored structure, the same uniform-λ limitation
as the AutoFerry urban cameras.

## 2026-06-12 — Backlog item 5: spatial clutter map (position maps on, bearing maps off)

**Change.** `ClutterMapSensorDetectionModel`
(`core/tracking/ClutterMapDetectionModel.hpp`, association.md §6): a
decorator over the fixed per-sensor table that learns spatially
varying λ_C online. Per (sensor, model), a sparse grid of cells each
holding a time-based EWMA (τ = 20 s, never scan-counted) of
unassociated returns per scan; cells touched by associated traffic
decay toward zero, untouched cells read back the table baseline.
`paramsFor(z)` — now virtual on the port; the TrackTree score already
called it, so the hot path is unchanged — interpolates λ at the
measurement position (bilinear ENU for position sensors, circular
azimuth for bearings) and clamps to [baseline/8, baseline·64].
`MhtTracker` enriches `ScanObservation` with scan time and the
unassociated subset of positions/azimuths. Bench ablation config
`imm_cv_ct_mht_cmap` = canonical IPDA+VIMM stack + map; the canonical
config and all defaults are untouched (verified: every non-cmap row of
baseline `2026-06-12_clutter_map` is bit-identical to
`2026-06-11_philos_resample`).

**Measured negative result — the bearing-map death spiral.** The first
run (`2026-06-12_clutter_map_bearing_spiral`) had bearing maps on and
collapsed lifetime on the camera-heavy autoferry scenarios (sc17
0.90 → 0.25, sc5 0.91 → 0.31, sc22 0.84 → 0.43, sc2 0.96 → 0.72).
Per-sub-map ablation (fixed vs full vs position-only vs bearing-only
on sc2/5/13/16/17/22) isolated it cleanly: position-only is
lifetime-neutral on every scenario; bearing-only reproduces the full
collapse. Mechanism: bearings cannot initiate tracks, so a target
whose track lapses keeps feeding "unassociated" bearings at its own
azimuth — the map raises λ exactly where the target is, suppresses
re-confirmation, and the suppression self-reinforces. The bearing
map's apparent OSPA gains (sc13 348 → 262) came from suppressing true
tracks alongside false ones. Bearing maps are therefore OFF by default
(`ClutterMapParams::enable_bearing_map`), opt-in only; re-enabling
requires a clutter proxy that excludes trackless targets
(hypothesis-level labeling, association.md §6 ways-to-improve).

**Result (`2026-06-12_clutter_map`, cmap vs canonical, position maps
only).** Acceptance was "OSPA ↓ without lifetime loss on true tracks":

- dense_clutter: OSPA 103 → 64.3 (−38%), breaks 0.35 → 0.2, switches
  0.45 → 0.2 — uniform Poisson clutter is exactly what the map learns.
- philos: OSPA 429.5 → 398.4, id_switches 0.17 → 0, pos_rmse
  38.5 → 34.4 (Boston-harbour radar shore structure absorbed).
- autoferry: lifetime preserved or up on all 9 (sc3 0.872 → 0.904,
  sc22 0.837 → 0.856); OSPA small moves both ways (sc13 −10.5, sc6
  −7.9, sc22 −4.6 vs sc16 +7.7, sc5 +6.7). Neutral overall — expected:
  the urban offender is the *cameras*, whose map is the disabled one.
- Clean synthetics: OSPA +5–11 (crossing 18.6 → 28.1, head_on
  18.6 → 27.8), lifetime −0.02. Cause: birth self-poisoning — a new
  target's first return is by definition unassociated, bumps its own
  cell from the 1e-6 floor to the 64× clamp, and delays confirmation
  by ~a scan. Inherent to the birth-gate clutter proxy (excluding
  birthing returns would also exclude all clutter, which births
  too); the fix is hypothesis-level labeling, same as above.

**Verdict.** `imm_cv_ct_mht_cmap` stays an ablation config; the
canonical config keeps the fixed table. The map is the right tool
where clutter is dense and roughly Poisson per cell (dense_clutter,
philos) and is safe-by-construction elsewhere (clamped, baseline
passthrough when untouched) — but the birth-gate proxy is too blunt
for camera bearings and slightly taxes clean-scene confirmation.
Promote only after the proxy reads the global hypothesis instead of
the birth gate.

## 2026-06-12 — Clutter map second iteration: global-hypothesis labeling

**Change.** Clutter evidence for the spatial map is now labeled from
the chosen global hypothesis instead of the birth gate: MhtTracker
builds the observe() bundle AFTER the solve, and each return carries
clutter weight 1 − r of the hypothesis that claims it (selected hit
leaf, or the tree it birthed this scan; 1.0 when unclaimed; the IPDA-
off sentinel r = 1 makes claimed returns weightless). ScanObservation
renamed its evidence fields (`clutter_positions/_weights`,
`clutter_bearings/_weights`); the map sums weights per cell. Fixed
models ignore observe(), so every non-cmap config is bit-identical
(verified against `2026-06-12_clutter_map`).

**Hypothesis test — does this re-enable the bearing map? NO.**
Original claim (this morning's entry): hypothesis labeling is the
precondition for the bearing map. Measured (per-scenario diagnostic,
bearing map opt-in): strictly WORSE than the binary proxy — sc17
lifetime 0.25 → 0.13, sc5 0.31 → 0.10. Root cause: a coasting or
freshly re-born track's claimed bearings carry weight 1 − r exactly
while r is low — the map feeds on the target during the occlusions
the track must survive; the binary proxy at least zeroed every gated
bearing. The spiral is structural until the weight can distinguish
"low-existence target" from "no target" (visibility-conditioned
weights or a hard zero for hypothesis-claimed returns —
association.md §6). Bearing maps stay opt-in-off; docs corrected.

**Result (`2026-06-12_clutter_map_hyplabel`, cmap vs the birth-gate
cmap of `2026-06-12_clutter_map`).** Better on 17 of 20 scenarios:

- Clean synthetics recover 15–30% of the birth tax (crossing
  28.1 → 26.9, crossing_dropout 35.0 → 31.8, overtaking 17.7 → 15.4;
  canonical-fixed remains lower still — the residual tax is the birth
  weight 0.5 plus low-r claims while a new track's existence climbs).
- dense_clutter OSPA 64.3 → 59.4 (fixed: 103), switches 0.2 → 0.1.
- autoferry: small broad gains (sc3 OSPA 440.5 → 433.8 with switches
  40 → 36.5, sc6 switches 69 → 63, sc22 26.5 → 23); lifetime
  unchanged everywhere.
- philos regresses 398 → 408 (still −21 vs fixed) with lifetime
  0.288 → 0.273: its vessels confirm slowly at P_D 0.07, so real
  returns are claimed at low r and charged as partial clutter — the
  same "low-existence target" signature as the bearing spiral, in
  miniature. The weight refinement above would address both.

**Verdict.** Keep hypothesis labeling (more principled, better
almost everywhere); cmap remains an ablation config. Next refinement
recorded: existence-vs-visibility-aware weights.

## 2026-06-12 — Backlog item 11: sc5 identity churn re-diagnosed (conveyor, not swaps)

**Investigation.** The 2026-06-11 hypothesis (camera bearings swapping
between two angularly-unresolved tracks in the global solve) was
tested and falsified in three steps:

1. **Shared ambiguous bearings** (`share_ambiguous_bearings`): a
   Bearing2D return whose hit branches exist in ≥ 2 trees is exempted
   from the solve's exclusivity (each tree's bearing hit maps to its
   private assignment column — both trees can consume it; the
   physically right model for merged camera detections). Measured on
   sc5: **bit-identical** despite 23k shared assignments — under
   exclusivity each tree was already taking its nearest bearing, so
   per-scan assignment swaps were never the churn.
2. **Switch forensics** (per-event dump): 182 raw events, only 21 are
   pair swaps. Dominant pattern: truth 1 is tracked by a *succession*
   of short-lived ids (~2 s apart, second-nearest track 50 m away —
   handoffs, not swaps), plus near-tie flicker (d1 10.7 vs d2 10.8 m).
   107 confirmed ids in 139 s for 2 truths.
3. **Birth forensics**: 45 of 48 near-truth confirmations occur with a
   live confirmed track already within 50 m — duplicate births. Gate
   sweep confirms gate escape: global gate 20 → 100 collapses sc5
   switches 91 → 27 (sc6 74 → 8.5) while OSPA *improves* ~80 m
   (duplicate cardinality), at the cost of rmse/lifetime.

**Conveyor mechanism.** Bearing-carried track drifts 10–30 m and turns
overconfident → sparse radar return misses the χ² gate → births a
duplicate alongside → young tree confirms and takes the stream → old
tree starves → handoff = id switch, every 2–4 s.

**Remedies implemented (opt-in, defaults OFF, canonical bit-identical;
574/574 tests green):** per-sensor static gate
(`DetectionParams::gate_threshold`), and the adaptive recapture gate
(`gate_recapture_tau_s`: position gate × min(max_scale, 1 + age/τ)
with age = time since the hypothesis' last position-sensor update,
anchor carried per tree node). Measured (τ = 2 s): switches/OSPA
improve strongly (sc5 91 → 43, OSPA −60 on most scenarios) but
lifetime regresses (sc3 0.87 → 0.63, sc17 0.90 → 0.54) and rmse
climbs to 30–60 m: the radar return gates back in but the Kalman gain
uses the same overconfident P and barely corrects. Gate widening
treats the symptom.

**Root cause, quantified (→ new backlog item 12).** NEES of near-truth
confirmed tracks on sc5: **mean 77.6** (consistent filter ≈ 2), 57% of
samples above the 99% χ² bound; claimed σ 1.2–3.8 m against 15.1 m
mean actual error. The filter is structurally overconfident on real
bearing-dominated data (suspects: camera R calibration, bearing-update
range collapse, synthetic-tuned process noise). Until item 12 lands,
none of the item-11 knobs is promotable — with honest covariance the
conveyor should not form at the base gate at all.

---

## 2026-06-16 — Schmidt-KF (item 9 follow-up) + per-target bench metrics

**What.** Two complementary changes:
1. **Per-target metrics.** Bench harness now emits per-truth-id rows
   for `lifetime_ratio`, `track_breaks`, `id_switches`, `pos_rmse_m`,
   `sog_rmse_mps`, `cog_rmse_deg`, `rmse_n` — suffix pattern
   `:truth_<id>`, mirroring the existing per-source NIS rows. Exposes
   "is the scenario mean dragged by one bad target or do all targets
   look the same" without re-running. Implementation in
   `core/benchmark/Metrics.{hpp,cpp}` + `Sweep.cpp`.
2. **Schmidt-KF "considered" bias treatment.** `applyBiasCorrection`
   used to subtract `b̂` but ignore `P_b`. Now it also inflates `R`:
   Position2D `R_eff = R + P_b`, Bearing2D/RangeBearing2D
   `R_eff[β,β] += σ_b²`. Extracted to shared
   `core/pipeline/BiasCorrection.hpp` so Tracker and MhtTracker
   cannot drift. Closes item 9 acceptance criterion 5.

**Why.** Without `P_b` folded in, the filter treats every corrected
measurement as if it had a perfect calibration — NIS dips below 1
right after the bias estimator first publishes (the exact regime
where `P_b` is still wide). The Schmidt correction restores
calibration in that window without re-introducing the bias state
into every track filter.

**Measured (`bench_schmidt_20260616T105707Z` vs the same biascal
config in `bench_perenv5_20260616T091213Z`).** Configs:
`imm_cv_ct_mht_biascal` on the AIS-anchored AutoFerry scenarios.

| Scenario       | GOSPA RMS   | GOSPA mean  | id_switches | NEES mean |
|----------------|-------------|-------------|-------------|-----------|
| sc2_anchored   | 3.465 →3.465 (–0.0%) | 2.255 →2.255 | 1 →1 | 2.32 →2.32 |
| sc3_anchored   | 1.731 →1.731 | 1.472 →1.472 | 0 →0 | 0.91 →0.91 |
| sc4_anchored   | 4.552 →4.552 | 2.718 →2.718 | 1 →1 | 3.64 →3.64 |
| sc5_anchored   | 4.274 →4.274 | 2.690 →2.689 | 5 →5 | 3.02 →3.02 |
| sc6_anchored   | 9.474 →9.473 | 6.189 →6.189 | 11 →11 | 4.34 →4.34 |
| sc13_anchored  | 5.845 →5.858 (+0.2%) | 3.244 →3.248 | **16 →14 (–12.5%)** | 67.0 →75.4 (+12.5%) |
| sc16_anchored  | 4.420 →4.419 | 2.417 →2.415 | 2 →2 | 2.76 →2.75 |
| sc17_anchored  | 4.493 →4.493 | 2.714 →2.713 | 1 →1 | 1.53 →1.53 |
| **sc22_anchored** | **6.744 →6.125 (–9.2%)** | 3.827 →3.452 (–9.8%) | **6.5 →6.0 (–7.7%)** | 1.13 →1.12 |

**NIS (mean → 1.0 is ideal):** shifts are small (third/second
decimal) but consistently **toward** the larger value on
non-anchor sources, i.e. inflated R lowers the normalised
innovation — the expected direction. The bias estimator publishes
with `P_b` already tight (default isotropic 0.01 m² after the
convergence window), so `R + P_b ≈ R` and the kinematic effect is
modest. The headline win is sc22: a 9% GOSPA RMS drop on the worst
anchored scenario without changing the filter.

**sc13 NEES +12.5% caveat.** sc13 already runs at NEES ≈ 67, far
above χ² ≈ 2. With looser R the gate accepts marginally more
measurements; on a structurally overconfident filter (R baseline
too tight, item 12 still partially open), some of the new
admissions degrade NEES further. id_switches improving by 12.5%
in the same scenario shows the gate-widening is net positive on
identity, just not on consistency — a known direction Schmidt-KF
alone cannot fix.

**Takeaway.** Schmidt-KF is a **correctness fix**, not a
performance lever. After it lands the filter is honest about bias
uncertainty; on anchored scenarios where `P_b` converges to small
values, the kinematic delta is correspondingly small. The big
arrow is the bias estimator itself (item 9, already shipped); the
Schmidt-KF block keeps that work from inverting calibration right
after the estimator publishes.

**Risk realised: low.** Added covariance only loosens gates; no
scenario regressed on GOSPA RMS by more than 0.2%, none lost
lifetime.

---

## 2026-06-16 — Per-target metrics shipped

**What.** `MetricsResult.per_truth` exposes per-truth-id values
for `lifetime_ratio`, `track_breaks`, `id_switches`, `pos_rmse_m`,
`sog_rmse_mps`, `cog_rmse_deg`, `rmse_n`. Bench emits one row per
(truth_id, metric) with the suffix pattern `<metric>:truth_<id>`,
mirroring the per-source NIS rows. Bench row count rose from
50628 → 79482 on the standard matrix; no schema change.

**Why.** Until this lands, "scenario mean of 67 NEES" was a single
number that hid whether one target was catastrophic or all targets
were bad. The per-target breakdown lets us read sc13's NEES,
sc17's `id_switches`, and the truth-anchor injection's effect
per ground-truth track id from the same CSV.

**Next.** Use the per-target NEES split on sc13 / sc17 / sc22 to
isolate whether the existing item-12 R calibration needs a
per-target refinement (e.g., a single small/far target dragging
the env-2 NEES distribution) or whether the whole filter is
miscalibrated uniformly. Tools to be added under
`tools/autoferry_per_target_inspect.py` if the split signals one
specific target.

---

## 2026-06-16 — Per-target diagnosis of the env-1/env-2 asymmetry

**Method.** Cross-referenced the per-truth rows from
`bench_schmidt_20260616T105707Z.csv` with per-scenario geometric
features (range to own-ship, lidar coverage fraction, per-sensor
detection count attributed to truth via nearest-neighbour in
30 m), then re-measured `imm_cv_ct_mht_bearguard` against the per-
truth metrics it had been shelved against the per-scenario
metrics.

**Asymmetry source.** 5 of 9 scenarios have one target 2–5× worse
on `pos_rmse_m` than the other. The worse target is **bearing-
dominated** in every case:

| Scenario | Worst tid | Lidar/Radar/Bearings | Diagnosis |
|----------|-----------|-----------------------|-----------|
| sc3 t1   | rmse 2.1× | 4 / 2 / 545           | bearing-dominated, range 172 m, 50% outside lidar |
| sc5 t1   | rmse 4×   | **0 / 0** / 517       | **pure BOT**, range 213 m, 76% outside lidar |
| sc6 t1   | rmse 5.1× | 90 / 20 / 594         | range 169 m, 57% outside lidar |
| sc16 t1  | rmse 4.8× | 54 / 11 / 486         | heading stdev 33° (manoeuvre-dominated) |
| sc17 t2  | 7 breaks  | 50 / 18 / 442         | identical geometry to t1 — pair / crossing |
| sc22 t2  | rmse 1.7× | 79 / 19 / 541         | close-pair association, not pure BOT |

The twins of the same scenarios suffer a *different* failure: ID
switch counts of 45 / 66 / 77 on well-instrumented targets — too
many measurements feeding JPDA/MHT solves between near targets
(association churn, JIPDA territory).

**BearingRangeGuard re-measured.** The guard had been shelved
against per-scenario averages. Per-truth measurement shows:

- sc22 t2 pos_rmse −20.7% (+ id_switches +54% — net wash)
- sc6 t2 pos_rmse −16.9%, lifetime +4pp, track_breaks −33% (the
  cleanest win but on the *healthy* twin, not the BOT target)
- sc5 t1 / sc6 t1: **bit-identical** to baseline — the guard
  activates on Bearing2D updates but its effect on the position
  covariance is reabsorbed by the IMM-CV-CT mode-mixing step.

Net: the guard stays opt-in. The original shelf decision is
confirmed, but the per-truth view shows the structural reason —
BOT range collapse is a Jacobian-rank problem at update time, not
a covariance-shape problem the guard can fix.

**Implication for the backlog.** True bearing-only fix needs:
- Modified-polar EKF on bearing-dominated tracks (track
  parameter is `1/r`, log-r, or polar (r, β) directly so the
  range-axis singularity is avoided), or
- Bearing-bearing triangulation between sensors *before* track
  initiation, to constrain the prior range with finite
  uncertainty rather than 1/0.

Association churn on the twin targets is a separate problem
(JIPDA/PMBM, deferred).

**Where this leaves the next step.** The per-target view cleanly
separates the two env-2 problems from each other. sc13 sits in
neither bucket — both targets are within lidar coverage at ~77 m,
well-instrumented, and still produce NEES = 75 anchored. That is
the only scenario where R calibration is the genuine bottleneck;
addressed next.

---

## 2026-06-16 — sc13 root cause: unobserved EO/IR bearing bias

**Method.** Ran `tools/autoferry_r_calibration.py` with a new
per-scenario report on sc13/16/17/22, then inspected the
post-bias bench NIS by sensor source.

**sc13 R is approximately right.** Lidar NIS = 0.84, radar NIS =
0.83 (target = 1, slightly conservative); empirical σ matches the
env-2 R override (lidar 2.99 vs configured 3.0, IR/EO 5.5°/5.2°
vs configured 5.3°). Radar empirical 3.32 m vs configured 5.0 m
(50% looser than necessary) — minor, not the bottleneck.

**The cameras have a 5–7° systematic bearing bias.** Per-scenario
empirical means:

| Scenario | IR mean bearing | EO mean bearing |
|----------|-----------------|-----------------|
| sc13     | **7.04°**       | **6.87°**       |
| sc16     | 3.59°           | 7.74°           |
| sc17     | 2.58°           | 7.85°           |
| sc22     | 3.56°           | 5.42°           |

At sc13's 77 m mean target range, a 7° bearing offset = ~9.4 m
across-LOS position error. The 9 m systematic offset is exactly
the magnitude needed to drive NEES from ≈1 to ≈70 with the
filter's claimed σ ≈ 0.5 m.

**Why the existing bias estimator didn't catch it.** Reading
`SensorBiasPairExtractor.hpp`'s docstring: bearing-only
contributions were **explicitly skipped** ("a future iteration
adds extractBearingPairs"). Item 9's 2026-06-15 ship landed the
Position2D path only — the EO/IR camera biases never had a
learning channel.

**Fix shipped.** `extractBearingPairs(tracks, time)` mirrors the
position-pair extractor for (AIS anchor) × (Bearing2D
contribution) pairs in the recent_contributions window. To carry
the bearing through the provenance side-channel,
`Track::SourceTouch` gained optional `alpha_rad` /
`alpha_var_rad2` fields (NaN sentinel; bit-compatible with
consumers that ignore them). Tests:
`SensorBiasPairExtractor.EmitsBearingPairFromAisAndEoirContributions`
+ `.SkipsBearingTouchesWithoutAlphaPayload`. Bench:
`bench_brgbias_20260616T135132Z.csv`.

**Measured deltas (biascal anchored vs Schmidt-KF only):**

| Scenario          | NEES mean       | GOSPA RMS    | pos_rmse_m   | id_switches |
|-------------------|-----------------|--------------|--------------|-------------|
| sc2_anchored      | 2.32 → 2.33     | 3.47 → 3.46  | 1.59 → 1.61  | 1 → 2       |
| sc3_anchored      | 0.91 → 0.90     | 1.73 → 1.73  | 1.17 → 1.18  | 0 → 0       |
| sc4_anchored      | 3.64 → 3.70     | 4.55 → 4.55  | 1.75 → 1.71  | 1 → 1       |
| sc5_anchored      | 3.02 → 4.02     | 4.27 → 4.53  | 1.60 → 1.90  | 5 → 3       |
| **sc6_anchored**  | 4.34 → 4.71     | **9.47 → 8.70 (−8.2%)** | 1.90 → 1.90 | **11 → 6** |
| **sc13_anchored** | **75.4 → 73.4 (−2.7%)** | 5.86 → 5.86 | 2.70 → 2.69 | 14 → 14 |
| sc16_anchored     | 2.75 → 2.68     | 4.42 → 4.39  | 1.13 → 1.07  | 2 → 2       |
| **sc17_anchored** | **1.53 → 1.18 (−22.6%)** | 4.49 → 4.40 | 1.29 → 1.18 | 1 → 2 |
| sc22_anchored     | 1.12 → 1.11     | 6.13 → 6.22  | 1.19 → 1.19  | 6 → 6       |

**sc17 / sc6 are the headline wins** — the bearing bias is
observed, learnt, and published; tracks lock onto the
corrected bearings and either ID stability (sc6: 11 → 6) or
filter consistency (sc17: 1.53 → 1.18 NEES) improves.

**sc13 stays catastrophic (NEES 73).** Why: the estimator's
random-walk process noise gives a steady-state σ ≈ 0.26°, just
below publish threshold 0.3°. To reach publish, the variance
needs enough cumulative pair observations to overcome the random
walk's variance injection. sc13 has 14 ID switches — each switch
resets `recent_contributions`, breaking the AIS-bearing pair
coupling on the affected track. The effective pair rate stays
too low; the bearing estimator's σ plateaus near the threshold
and never publishes. sc17 has 1 switch and reaches publish
easily.

**Followup candidate (deferred):** seed the EO/IR priors from
the offline-calibration values (env-2 EO ≈ 7°, IR ≈ 5°) via
`setKnownBearingBias`. The estimator already supports this
("setKnown" seeds prior, observations refine). Closes sc13
without changing the runtime; clean per-deployment calibration
workflow.

**No GOSPA / lifetime regressions worth noting.** Worst movement
is sc5 GOSPA +6%; lifetime unchanged across all scenarios. The
small NEES rises on sc4/sc5/sc6 are filters going from "too
tight" (NEES 3-4) to "slightly more so" because the bearing
update now contributes information the filter wasn't accounting
for; cosmetic, not load-bearing.

## 2026-06-17 — Item 13 cross-sensor extractor: review fixes (bench-neutral)

Three correctness findings on the cross-sensor anchored extractor
(`extractCrossSensorPositionPairs`, committed in `5d467cf`) were
fixed:

1. **One observation per calibrated key per cycle.** The original
   walked every ordered pair, so each key `X` got `N−1` KF updates per
   cycle all reusing the *same* sample `z_X` — correlated residuals
   folded as independent → `P_X` collapses too fast → premature
   publish. Now each key is anchored on its single most-trusted
   partner. `N=2` is provably identical to before; only `N≥3` changes.
2. **Never anchor across the same physical sensor.** ARPA TTM/TLL
   share a `source_id` but are distinct `SensorKind`s → their pair
   residual is ≈ noise regardless of the true shared offset, masking
   common-mode radar bias. Same-`source_id` anchoring is now skipped.
3. **Deterministic emission order** (`std::map`, not
   `unordered_map`) per CLAUDE.md invariant #4.

### Bench impact: none on the current matrix

The synthetic + AutoFerry scenarios all carry **N=2 positional keys
with distinct source_ids** (radar `autoferry_radar`, lidar
`autoferry_lidar`; no TTM/TLL split). For `N=2` all three fixes are
behavioral no-ops. Verified directly: rebuilt `5d467cf` (pre-fix) vs
`d1c46a1` (post-fix) **on the same host/build** are **byte-identical**
across `imm_cv_ct_mht × {sc2, sc2_anchored, sc22}` (cols
config..unit). The fixes' real effect lives in the `N≥3` /
same-hardware paths, which the matrix does not exercise — those are
covered by the new unit tests (`CrossSensorEmitsOneObservationPerKey`,
`CrossSensorSkipsSameSourceIdHardware`,
`CrossSensorSameHardwareAnchorsOnThirdSensor`,
`CrossSensorEmitsKeysInDeterministicOrder`). 637 ctest cases green.

### Baseline-reproducibility caveat (pre-existing, not introduced here)

The committed `docs/baselines/bench_xsensor_20260617T183817Z.csv` does
**not** reproduce bit-for-bit on this host: e.g. `imm_cv_ct_mht / sc2 /
nees_mean` reads `56.16` in the CSV but `1210.19` on a fresh rebuild of
its *own* commit. The CSV's provenance header is
`host/compiler/git_sha: unknown`, i.e. it was produced by a different
build. AutoFerry MHT is chaotic (gating + Murty branch order), so
sub-ULP FP differences between builds (FMA/`-march`/Eigen version)
amplify into large swings on the already-pathological autoferry NEES
(50–2340 across scenarios, both builds). This is a baseline-hygiene
issue — when a bit-reproducible reference is needed, regenerate the
full matrix on-host and pin the toolchain in the provenance block.

## 2026-06-20 — Post-UKF canonical floor pinned: `cl26_canonical_postukf_20260620.csv`

Half-day prerequisite for Cl-3 (PMBM) work — a clean comparison floor
against the new UKF canonical (`imm_cv_ct_mht` IS UKF post-2026-06-20)
so every downstream PMBM A/B is read against a single labeled baseline.
Same bench shape as `cl23_ukf_full_20260619.csv` (20 configs × 29
scenarios × seed 0 = 30 030 rows).

### Unexpected finding: the post-cl23 cross-sensor commits were NOT bench-neutral

Diff `imm_cv_ct_mht / gospa_mean` between `cl23_ukf_full_20260619` and
`cl26_canonical_postukf_20260620` reveals systematic deltas across the
five intervening cross-sensor-bias commits (a27ade8, d1c46a1, b01bedb,
44ba15c, 5d467cf). The 2026-06-17 cross-sensor review-fixes entry above
claimed bench-neutral because the matrix has N=2 positional keys per
scenario — but the post-cl23 changes touch the **same N=2** path:

| Scenario class | Direction | Magnitude | Mechanism (best read) |
|---|---|---|---|
| autoferry unanchored (9/9) | improved | −12.3 % mean (sc17 −20.4 %, sc22 −22.5 %, sc3 −16.0 %, sc4 −16.1 %, sc6 −13.9 %) | cross-sensor bias commits collectively tighten real-data bias correction |
| autoferry anchored | flat | ≤ ±2 % | anchored seeds the bias prior; cross-sensor extractor has little to add |
| philos | improved | −4.4 % | real-data trend matches autoferry |
| synthetic clean (crossing, head_on, overtaking, parallel, speed_change) | regressed | +9 to +16 % small absolute (e.g. crossing 8.5 → 9.9 m GOSPA) | `44ba15c` "one update per key/cycle (fix overconfidence)" → larger residual `P_b` → larger Schmidt-KF R-inflation → slightly looser updates on clean data where there is no real bias to correct away |
| dense_clutter / ais_dropout / clock_skew | regressed | +5 to +8 % | same mechanism as synthetic clean |
| non_cooperative | unchanged | 0.00 % | single-sensor → no cross-sensor bias path engaged |

Net interpretation: the post-cl23 changes are a **real win on the data
that matters** (autoferry + philos, where real biases exist) at the cost
of a small, theory-consistent regression on clean-synthetic. Direction
is correct; reverting to recover the synthetic numbers would forfeit
the autoferry wins. `cl26_canonical_postukf_20260620.csv` is the
post-UKF + post-bias-overconfidence-fix canonical floor — read all
Cl-3 PMBM A/Bs against this CSV, not against `cl23_ukf_full`.

### What this also means

The "bench-neutral" claim on the 2026-06-17 review-fixes commit and
the subsequent four commits (d1c46a1 through 5d467cf) was based on
spot-checks of a few scenarios; the full-matrix diff was not run.
Going forward, any commit that touches the bias path or the
measurement-correction path should produce a full-matrix bench diff
in the same commit, not a spot-check. The autoferry-unanchored wins
that emerged here would have been worth highlighting at the time of
landing rather than being hidden inside "no change".

## 2026-06-24 — Cl-3 #3: PMBM-vs-MHT runtime measurement and promotion call

**Why.** PMBM accuracy was known (`pmbm_adapt_k3_phase9_20260623` and
prior). Runtime was never measured at full-matrix scale, so the
canonical-promotion question was open. `Sweep.cpp` extended to emit
`wall_seconds` per (config, scenario, seed) cell; full 23×29 matrix
re-run at `--seeds 3`, baseline pinned at
`docs/baselines/cl3_timing_pmbm_vs_mht_20260624T062343Z.csv` (elapsed
4028 s, 1127 runs).

### Per-class median wall-seconds and PMBM/MHT ratio

| class | n | mht_med_s | pmbm | pmbm_adapt | pmbm_adapt_k3 |
|---|---:|---:|---:|---:|---:|
| autoferry_anchored   | 9 |  7.753 | 0.07x | **0.06x** | 0.66x |
| autoferry_unanchored | 9 |  3.211 | 0.14x | **0.10x** | 1.31x |
| philos               | 1 | 33.446 | 0.90x | **0.71x** | **10.68x** |
| dense_clutter        | 1 |  0.021 | 1.82x | 0.47x | 3.83x |
| non_cooperative      | 1 |  0.002 | 0.09x | 0.71x | 5.73x |
| synthetic            | 7 |  0.003 | 0.82x | 0.75x | 2.03x |

### Per-class median GOSPA delta vs MHT canonical (negative = better)

| class | pmbm | pmbm_adapt | pmbm_adapt_k3 |
|---|---:|---:|---:|
| autoferry_anchored   | +21.9% |  +5.1% | +10.9% |
| autoferry_unanchored | −38.2% | **−42.0%** | **−43.0%** |
| philos               | +42.8% | +19.0% | +18.8% |
| dense_clutter        | +102.5% | +3.1% | −1.3% |
| non_cooperative      | −28.2% |  +0.0% |  +0.3% |
| synthetic            |  −3.8% |  −3.8% |  −3.8% |

### Read

1. **`pmbm_adapt` (K=1) is faster than MHT on every scenario class.**
   Autoferry runs 7-16x faster, philos 1.4x faster, synthetics ~30%
   faster. The autoferry speedup grows with scenario length: the
   biggest single cell is sc5_anchored at **MHT 30.8 s → PMBM 0.79 s
   (39x faster)**, with sc3_anchored 14.9 s → 0.55 s (27x). MHT's
   cost-matrix enumeration scales worse with track-count + clutter
   density than PMBM's PPP+MBM structure.

2. **K=3 + xparent is dominated on runtime.** philos jumps from MHT
   33 s to **357 s (10.7x slower)** — the per-track-hypothesis
   expansion under K=3 hits philos's long replay duration hard. Same
   accuracy as K=1 on autoferry_unanchored (−43% vs −42%), strictly
   worse on philos accuracy AND runtime. The xparent fix recovered
   the autoferry-anchored regressions but the runtime cost on
   long-replay workloads is now visible: K=3+xparent is the wrong
   default for any consumer running scenarios > ~10 s.

3. **Accuracy direction unchanged from prior bench rounds.** PMBM
   wins big on autoferry_unanchored (−42%), regresses philos
   (+19%), and is essentially tied on synthetics. The
   autoferry_anchored regression of K=1 (+5%) is now small enough to
   be in the noise; the K=3 fix is no longer load-bearing.

### Promotion call

**Recommendation: keep `imm_cv_ct_mht` (UKF) as the default canonical
in `defaultConfigs()`, but document that `imm_cv_ct_pmbm_adapt` is
the recommended choice for autoferry-class workloads.** Reasoning:

- For autoferry deployment, `pmbm_adapt` strictly dominates MHT
  canonical: better GOSPA (−42% unanchored, +5% anchored ≈ tied),
  10-15x faster wall-clock. If the deployment-target workload is
  autoferry-class (littoral fusion of AIS + radar + EO/IR + lidar
  with multi-target close-pass scenarios), `pmbm_adapt` is the
  obvious choice.
- For philos-class workloads (single-sensor or longer-duration
  replays), MHT canonical still wins on accuracy (+19% GOSPA
  regression under PMBM) at acceptable runtime cost.
- The synthetic test suite barely separates the two; both are <1%
  of MHT runtime on those.
- Promoting `pmbm_adapt` to canonical would silently regress philos.
  Promoting `pmbm_adapt_k3` to canonical would silently make philos
  10x slower for no accuracy gain. Neither move is safe as a
  one-line `defaultConfigs()` change.

**Concrete next step.** Add a one-paragraph deployment-guidance note
in `core/benchmark/Config.cpp` next to `imm_cv_ct_pmbm_adapt` that
calls out the autoferry dominance + philos regression so library
consumers see it at the point of decision. Optionally: deprecate
`imm_cv_ct_pmbm_adapt_k3` to ablation-only status (still exposed
behind a build flag for the structural-refactor follow-up, but
removed from `defaultConfigs()` because of the 10.7x philos cost
with no accuracy upside).

Cl-3 #3 status: **measured and decided** — PMBM `pmbm_adapt` is the
recommended choice for autoferry-class deployment; MHT canonical
stays the default to avoid silent philos regression; K=3+xparent
deprecated from `defaultConfigs()` over runtime cost. The Cl-3
"PMBM is competitive with deployment-class MHT on real maritime
data" headline is supported across both axes (accuracy + runtime)
on autoferry; the philos accuracy gap remains the documented
honest caveat.

---

## Task 4 — PMBM coverage/visibility channel (ISensorActivity): measured 2026-06-29

**What shipped (code, Tasks 1–6, HEAD 44d3978).** A nullable `ISensorActivity`
port + `DeclaredSensorActivity` declared-profile provider; numeric
`platform_id` identity on `AssociationHints`; a unified PMBM identity gate
(same vessel if shared `mmsi` OR `platform_id`); per-duty-cycle surveillance
miss (replaces the wrong per-blip `compute_miss_pD` + `idle_halflife_sec`
when `use_sensor_activity=true`); an existence-neutral cooperative
stale/comms-loss signal (`IStaleSignalSink`) with cooperative-only retirement
by `cooperative_stale_timeout_sec`. All behind flags; default-off bit-identical;
determinism preserved (snapshot-read + deferred-write of the per-Bernoulli
activity-check times → hypothesis-order-independent). Full unit suite green
except the 2 known pre-existing adaptive-birth determinism fails.

Bench config `imm_cv_ct_pmbm_coverage` = the bundle base (birth_target=0.1,
source_aware_identity) with `use_sensor_activity=true`, `idle_halflife_sec=0`,
`dedup_miss_pd=false`, `cooperative_stale_timeout_sec=120`. Activity profiles
declared in `Sweep.cpp` from each scenario's detection table: surveillance
(ArpaTtm duty 2.5 s / EoIr 1.0 s / Lidar 0.1 s, coverage+p_D from the table),
cooperative (Ais interval 10 s). Cadence values are declared/tunable
(spec roadmap §13.1 adaptive provider).

**Philos A/B (single-seed; bench `2026-06-29_philos_coverage_ab.csv`,
`philos`/`philos_radartruth` identical):**

| config | gospa_mean | card_err | gospa_false | id_switch |
|---|---|---|---|---|
| birthtarget (Task 1) | **48.5** | −7.8 | 390 | 0 |
| adapt | 82.6 | +17.5 | 5150 | 0.09 |
| bundle (Task 2) | 112.0 | +46.3 | 11420 | 0.04 |
| **coverage (Task 4)** | **153.6** | **+107.9** | **23750** | 0 |

**Coverage is the worst PMBM variant on philos — a strong negative result.**
Massive over-count. Two compounding causes, the second fundamental:
1. *AIS immortality (plumbing gap).* AIS is modeled as cooperative-announce
   (correct per spec taxonomy), so its silence never lowers existence. But the
   cooperative retirement timer (`last_cooperative_touch_`) keys on
   `SensorKind::Cooperative` — philos AIS is `SensorKind::Ais`, so the timer
   never starts and AIS tracks are never retired. Proven by the isolation run
   `2026-06-29_philos_coverage_t15.csv`: dropping the timeout 120→15 s changed
   the result by **zero** (153.565 either way) — the timer is inert for AIS.
2. *Honest radar miss is too weak at philos p_D.* Philos radar p_D=0.07, so one
   missed sweep barely moves existence (`r⁺≈0.93·r`), and persistent shore
   returns are *re-detected every rotation* — the temporal coverage model
   cannot distinguish a re-detected shore echo from a real vessel. Removing the
   (dishonestly aggressive) wrong-math + idle_halflife removed the only thing
   that was suppressing those phantoms. This is the same lesson as Task 2c
   (correct math worse on philos) and Task 3 (clutter map inert on philos):
   **philos over-count is a spatial clutter problem, not a temporal one.**

**Autoferry guard (scenario2/22 ± anchored; `2026-06-29_autoferry_coverage_guard.csv`):**

| config | scen2 gospa | scen22 gospa | scen2 card_err | id_switch |
|---|---|---|---|---|
| adapt | 17.28 | 21.39 | +0.39 | 5–18 |
| bundle | 12.88 | 15.74 | −0.55 | 0–5.5 |
| **coverage** | **11.33** | **15.28** | **+0.15** | **0–1.5** |

**Coverage is best-in-class on the real open-water/urban autoferry scenes** —
lowest gospa, near-zero cardinality error, fewest id-switches — and with
*fewer knobs* (no idle_halflife, no wrong-math). On the two synthetic
*anchored* test scenes it trails the bundle slightly (4.98 vs 2.64; 3.12 vs
2.20) but is well-behaved. Where detection probability is real (autoferry
p_D 0.6–0.8), the honest coverage model genuinely works.

**Decision (Task 8): keep `imm_cv_ct_pmbm_coverage` as an opt-in ablation;
do NOT promote to canonical.** It is the recommended PMBM choice for
high-p_D, surveillance-dominated deployments (autoferry-class), where it
beats the bundle on accuracy, cardinality, and identity stability with a
simpler knob set. It must not be used for low-p_D / clutter-heavy coastal
workloads (philos-class), where it badly over-counts. The principled philos
fix is **spatial shore-clutter suppression (coastline land-masking / a
clutter-prior at birth + occlusion in the coverage query)**, not better
temporal miss modeling — recorded as the next candidate.

**Known limitations / follow-ups.**
- AIS-as-cooperative retirement timer gap (cause #1): the cooperative
  stale/retirement path recognizes only `SensorKind::Cooperative`, not other
  cooperative-announce sources (AIS). To make the coverage model viable on
  AIS-heavy scenes, the timer should key on the *channel kind* (from the
  activity profile), not the SensorKind. Deferred — would not change the
  philos verdict because radar phantoms (cause #2) dominate.
- CORRECTION (2026-06-30): the long-suspected "PMBM adaptive-birth
  non-determinism" was a FALSE ALARM. Tests #314/#770 were byte-comparing the
  `wall_seconds` wall-clock timing metric (which legitimately varies run-to-run);
  every tracker accuracy/cardinality metric is bit-identical across runs
  (instrumented + verified, commit e804470). The tracker is deterministic and
  the CLAUDE.md invariant was never violated — so these single-seed A/B numbers
  are REPRODUCIBLE, not noisy. The autoferry/philos gaps are real signal.

---

## Task A — PMBM land/coastline clutter-prior: measured 2026-06-30

**What shipped (code).** Nullable `ILandModel::clutterPrior(enu)→double` port; pure
`CoastlineGeometry` (signed-distance shoreline ramp: ≈0.5 at waterline, plateau 1.0
only well inland, 0 offshore); `CoastlineModel` (`ILandModel`+`IDatumChangeSink` — datum
recenter swaps the query datum, geometry stays geodetic); GeoJSON adapter (nlohmann,
already a dep; new `navtracker_land` lib). PMBM birth suppression scales the adaptive-birth
intensity `lambda_birth`/`rho_target` by `(1−c)` and inland-hard-drops (`c>0.95`), in both
candidate builders — acting on birth intensity NOT λ_C (Task 1's `birth_existence_target`
decouples r_new from λ_C). All behind `use_land_model` (default off, bit-identical). Coastline
fixture: `tests/fixtures/philos/boston.geojson` (City-of-Boston polygons; 86% of philos radar
plots fall on/near its land — see the 2026-06-29 pre-check).

**Philos A/B (single-seed; `docs/baselines/2026-06-30_philos_land_ab.csv`):**

| config | gospa | card_err | gospa_false |
|---|---|---|---|
| birthtarget (Task 1; wrong-math brake) | 48.5 | −7.8 | 390 |
| coverage (honest, no land) | 153.6 | +107.9 | 23750 |
| **coverage + land** | **73.1** | **+6.9** | **3550** |
| adapt | 82.6 | +17.5 | 5150 |
| bundle | 112.0 | +46.3 | 11420 |
| (MHT canonical, historical) | ~69.4 | — | — |

**The land model works decisively.** Added to the honest coverage stack it collapses the
over-count: card_err **+107.9 → +6.9** (~94% gone), gospa_false **23750 → 3550** (−85%),
gospa **153.6 → 73.1** (−52%). coverage+land now beats adapt and bundle and is near MHT
(69.4) — the first **honest, no-crutch** PMBM config that is competitive on philos. This is
direct end-to-end confirmation of the 2026-06-29 spatial-clutter diagnosis.

**Autoferry guard (`docs/baselines/2026-06-30_autoferry_land_guard.csv`):** coverage+land is
**byte-identical** to coverage on all four autoferry scenes (gospa 11.327 / 15.279 / 4.976 /
3.115) — the land model is correctly inert where no coastline fixture exists. No regression.

**Experiment — birthtarget + land (`docs/baselines/2026-06-30_philos_birthtarget_land.csv`):**
**byte-identical to birthtarget** (48.5 / −7.8 / 390). The land model has zero effect on top of
birthtarget. Interpretation: birthtarget's wrong-math `compute_miss_pD` already kills the on-land
phantoms (it over-suppresses → card_err −7.8), so suppressing those births earlier via the land
mask is redundant; birthtarget's residual 390 false-mass is NOT on land. **The land model is the
*honest substitute* for the wrong-math miss, not an addition on top of it.** (Experimental config
reverted; finding kept here.)

**Decision.** The land model is **validated and adopted** as `imm_cv_ct_pmbm_coverage_land`
(opt-in). It is the recommended **honest / no-crutch** philos-class config: it removes the
spatial clutter at its source, beats adapt/bundle, and approaches MHT — without the wrong-math
miss or `idle_halflife`. Caveat: the dishonest birthtarget (48.5) still edges coverage+land
(73.1) on single-seed philos gospa, because its over-aggressive wrong-math also kills the
residual *water/near-shore* clutter (gospa_false 390 vs 3550) that the land mask does not cover.
Closing that last gap is a tuning/next-step item (tighter offshore margin, or coverage-side
near-shore handling), not a defect in the land model. Determinism holds (tracker is deterministic;
2026-06-30 wall_seconds correction); these single-seed numbers are reproducible.

## 2026-06-30 (Project E, synthetic shore-clutter bench) — [Cl-2][Cl-3] Geometry breadth (5 new scenarios, PMBM vs MHT) + shore-clutter A/B (land ON/OFF on perfect-truth synthetic data); near-shore validator exposed + quantified the offshore no-birth-zone boundary (A1 fix tried, rejected on philos; B adopted)

**Premise.** Project E adds 7 synthetic scenarios to `defaultSimScenarios()`: geometry breadth
(`parallel_lanes_dense`, `crossing_30/60/90`, `convoy_overtake`) and shore clutter
(`shore_clutter_open`, `shore_clutter_nearshore`). The shore scenarios inject 30 stationary
clutter points in-land with P_D=0.9, plus real targets in open water (`open`) / 60 m offshore
(`nearshore`, after the resolution below).
The synthetic coastline (Boston-style polygon at shore_y=500m, offshore_halfwidth=50m,
inland_halfwidth=50m) is built in-memory; no fixture file is needed.

**Method.** `runSweep` over 5 seeds. Configs: `imm_cv_ct_mht` (Cl-2 reference),
`imm_cv_ct_pmbm_coverage` (PMBM, land OFF), `imm_cv_ct_pmbm_coverage_land` (PMBM, land ON).
All means are over seeds 0–4.

### Geometry breadth: PMBM vs MHT (5 new scenarios)

| Scenario | Config | gospa_mean | card_err | lifetime_ratio | id_switches |
|---|---|---:|---:|---:|---:|
| parallel_lanes_dense | MHT | 17.70 | −0.43 | 0.883 | 3.4 |
| parallel_lanes_dense | PMBM | **14.20** | −0.10 | **0.975** | **0** |
| crossing_30 | MHT | 10.79 | −0.095 | 0.948 | 1.6 |
| crossing_30 | PMBM | **10.00** | −0.050 | **0.975** | 1.2 |
| crossing_60 | MHT | 9.96 | −0.055 | 0.973 | 1.2 |
| crossing_60 | PMBM | 10.04 | −0.055 | 0.973 | **0.8** |
| crossing_90 | MHT | 9.91 | −0.055 | 0.973 | 0.4 |
| crossing_90 | PMBM | 9.91 | −0.055 | 0.973 | 0.4 |
| convoy_overtake | MHT | 9.25 | −0.063 | 0.983 | 0.3 |
| convoy_overtake | PMBM | **9.16** | −0.067 | 0.983 | **0** |

**Verdict.** No regression on any geometry scenario. PMBM wins clearly on `parallel_lanes_dense`
(GOSPA −20%, id_switches 3.4→0, lifetime 0.883→0.975 — the close-spacing target-merge failure
mode of MHT is exactly what PMBM's multi-Bernoulli formulation avoids). On low-angle crossings
(30°) PMBM recovers more cleanly (lower GOSPA, no id-switch inflation). On 60°/90°/convoy the
two are equivalent within noise. The breadth does not surface any new PMBM regression.

### Shore-clutter A/B: land model ON vs OFF (perfect-truth synthetic data)

| Scenario | Config | gospa_mean | gospa_false | card_err | lifetime_ratio |
|---|---|---:|---:|---:|---:|
| shore_clutter_open | PMBM land OFF | 76.40 | 5811 | +29.00 | 0.975 |
| shore_clutter_open | **PMBM land ON** | **9.69** | **1** | **−0.05** | **0.975** |
| shore_clutter_nearshore | PMBM land OFF | 75.94 | 5810 | +29.025 | 0.975 |
| shore_clutter_nearshore | **PMBM land ON** | **6.55** | **0** | **−0.025** | **0.975** |

(`shore_clutter_nearshore` shown after the resolution below — the validator target sits 60 m
offshore, routed clear of the pier; MHT reference omitted for brevity, tracks like land-OFF.)

**Verdict (PASS, both scenarios).** Land ON is decisive: card_err collapses from +29 to ~0 (all
30 inland clutter tracks eliminated), gospa_false 5810→≤1, GOSPA 76→7–10. Real targets — the two
crossing vessels at y=100 m in `open`, and the single vessel 60 m offshore in `nearshore` —
survive with lifetime_ratio=0.975. This is the clean perfect-truth confirmation of the philos
real-data land-model result.

### The near-shore finding, and why the validator now sits at 60 m

The first cut of `shore_clutter_nearshore` placed the real target **10 m** offshore (y=490).
With land ON it was **never tracked** (lifetime_ratio=0, all 5 seeds) — and the validator
existed precisely to catch this. Root cause (confirmed in code):

- At 10 m offshore, c = (W_off − d)/(W_off + W_in) = (50−10)/100 = **0.40**, so land_scale = 0.60.
- `birth_existence_target = 0.1` ⇒ unsuppressed r_new ≈ 0.1; after land scale, r_new ≈ **0.0625**.
- `min_new_bernoulli_existence = 0.1`. Since 0.0625 < 0.1, the phantom-birth gate
  (`PmbmTracker.cpp`) drops the birth — every scan.

Because the gate **equals** `birth_existence_target`, *any* soft suppression (c>0) pushes a birth
below the gate: the entire offshore soft band (`offshore_halfwidth_m` = 50 m) is a **no-birth
zone** under `coverage_land`. A vessel within 50 m of shore will not initiate.

**A1 (tried, rejected).** Decouple the gate below the target — `min_new_bernoulli_existence`
0.1 → 0.05 — so a softly-suppressed real near-shore birth (0.0625) survives. On the synthetic
bench this works (the 10 m target is revived). But the **philos guard regressed materially**
(single-seed, `imm_cv_ct_pmbm_coverage_land`):

| floor | philos gospa | card_err | gospa_false |
|---|---:|---:|---:|
| 0.10 (kept) | **73.1** | **+6.9** | **3550** |
| 0.05 (A1) | 100.0 | +36.2 | 9000 |

Lowering the gate re-admits philos near-shore *water* clutter that the 0.1 gate used to kill
(only *on-land* clutter is hard-gated; the offshore-ramp residual is what the gate caught) —
roughly a third of the land model's deployment value lost. A1 rejected.

**B (adopted).** Keep the 0.1 gate (preserve the philos win) and accept the <50 m no-birth zone
as a documented limitation — near-land operation is rare in this deployment. The validator is
reframed: the real target now travels **60 m offshore** (y=440, c=0), routed in x∈[−500,−260] to
stay clear of the pier (which protrudes to y=350 at x∈[−20,20]). It now verifies the operative
guarantee — the land model removes the shore clutter **without collaterally suppressing a
legitimate vessel just outside the band** — and passes (lifetime 0.975). The committed test
`SyntheticClutterAB.LandModelRemovesShoreOverCountKeepsRealTargets` is **green**.

**Takeaway.** The land-clutter prior is confirmed on perfect-truth synthetic data, and the bench
quantified its boundary: under `coverage_land` (gate == target) the soft offshore band is a
no-birth zone, so vessels within `offshore_halfwidth_m` (50 m) of shore — or near the pier — do
not initiate. Reviving them by lowering the gate trades away the philos real-data win, so it is
not done. Philos itself is unaffected (its real ships sit far enough offshore that c≈0).

## 2026-06-30 (Project E follow-up) — Correct-math (`dedup_miss_pd`) + land A/B: the flag is INERT in `coverage_land` (coverage model owns the miss path)

**Question.** Does the land prior finally let us run the *correct* misdetection
math (`dedup_miss_pd=true`) on philos without the regression that turning it on
caused historically (gospa 112–119)? I.e. has the "wrong miss-P_D was the
load-bearing brake" situation been resolved?

**Method.** A/B `imm_cv_ct_pmbm_coverage_land` with `dedup_miss_pd` OFF (shipped)
vs a copy with `dedup_miss_pd=true`, both with the land model, on philos (real)
and all 10 autoferry scenarios.

**Result — byte-identical, every scenario.**

| scenario | metric | dedup OFF | dedup ON |
|---|---|---:|---:|
| philos | gospa / card_err / false | 73.06 / +6.90 / 3550 | **73.06 / +6.90 / 3550** |
| autoferry_scenario2 | gospa / card | 11.33 / +0.15 | **11.33 / +0.15** |
| autoferry_scenario17 | gospa / card | 18.40 / −0.98 | **18.40 / −0.98** |
| (all 10 AF scenarios) | every metric | — | **identical to OFF** |

**Why (confirmed in code).** `coverage_land` sets `use_sensor_activity=true`.
In `PmbmTracker.cpp` the miss-detection update branches on that flag: when on
(line ~660) the existence update goes through `sensor_activity_->evaluate(...)`
(surveillance-miss logic with the channel's p_D) and **never calls
`compute_miss_pD`** — which is the only place `dedup_miss_pd` is read (line ~614).
The legacy `compute_miss_pD` path (line ~714) runs *only* when
`use_sensor_activity==false`. So under the coverage model the dedup flag is dead
code.

**Takeaway (answers the "broken math" question).** In the recommended honest
PMBM config the broken-vs-correct miss-P_D distinction is **moot**: the coverage /
sensor-activity model has *replaced* that entire mechanism. `coverage_land`'s
philos win (gospa 73, card_err +6.9) rests on the coverage miss-handling + the
land prior, **not** on the legacy wrong-math crutch — and not on the corrected
math either; that code path simply isn't exercised. The "wrong miss-P_D is the
load-bearing brake" finding (2026-06-24) applies to the *legacy-path* configs
(no sensor-activity, e.g. `bundle`), where enabling `dedup_miss_pd` still
regresses philos. There it remains quarantined. Net: the crutch is **out of the
recommended path by replacement**, not by fixing-and-enabling correct math —
those two live in mutually-exclusive code paths, so "correct-math + land" cannot
be combined in `coverage_land` as posed. Minor follow-up: `dedup_miss_pd` should
carry a comment that it is inert under `use_sensor_activity`.

## 2026-06-30 (Project E follow-up) — `bundle + land`: correct-math + land prior, no coverage → best HONEST philos result, beats MHT

**Question.** `coverage_land` bypasses `dedup_miss_pd` (coverage owns the miss path), so it couldn't test "correct math + land." The legacy path CAN: `imm_cv_ct_pmbm_bundle` runs `dedup_miss_pd=true` (correct math) but regressed philos to gospa 112 because correct math removed the wrong-math phantom brake and nothing replaced it. Does the land prior serve as that replacement brake?

**Method.** A/B `imm_cv_ct_pmbm_bundle` vs `bundle + use_land_model` (= new config `imm_cv_ct_pmbm_bundle_land`), philos (real) + all 10 autoferry scenarios. Single-seed.

**Result — yes, decisively, on philos.**

| config | philos gospa | card_err | gospa_false | life |
|---|---:|---:|---:|---:|
| imm_cv_ct_pmbm_bundle (correct math, no land) | 111.99 | +46.25 | 11420 | 0.030 |
| **bundle_land (correct math + land)** | **59.49** | **−2.95** | **1580** | 0.030 |

Land cuts bundle's philos gospa 112→59.5 (−47%), card_err +46→−3, false 11420→1580. Autoferry: **byte-identical to bundle** across all 10 scenarios (autoferry declares no coastline → land inert), so the correct-math clean-data advantage is fully preserved.

**Significance.** 59.5 is the **best HONEST philos number to date** — correct misdetection math, principled spatial brake, NO wrong-math crutch, NO coverage machinery. It beats `coverage_land` (73.1), `adapt` (82.6), and — for the first time for an honest no-crutch config — **MHT (69.4)**. The only lower number, `birthtarget` (48.5), is dishonest (leans on the wrong-math brake). So among honest configs, `bundle_land` is now the philos leader.

**Mechanism.** On the legacy (non-coverage) path `dedup_miss_pd` is live, so correct math removes the over-suppressing brake; the land prior then hard-gates the on-land phantoms at birth. This is the genuine "correct physics + principled brake" combination — the substitution that `birthtarget+land` couldn't show (there the wrong-math brake was still present, making land redundant; eval-log 2026-06-30 "birthtarget + land").

**Shipped** as `imm_cv_ct_pmbm_bundle_land` (config count 28→29). **Caveats before any "make it default" decision:** (1) single-seed — no error bars on the 59.5 vs 69.4 margin (see 2026-06-30 "enough tests" discussion); (2) the philos win is **conditional on a coastline GeoJSON being wired** — without one, bundle_land falls back to bundle (which over-counts on coastal clutter, gospa 112); (3) not yet measured on the 17 synthetic scenarios. Default-promotion decision deferred.

## 2026-06-30 (Project E follow-up) — Gate 1: `bundle_land` across all 17 synthetic scenarios → workload-specific, NOT a universal default

**Method.** `imm_cv_ct_mht` (canonical) vs `imm_cv_ct_pmbm_adapt` (PMBM baseline) vs `imm_cv_ct_pmbm_bundle_land`, all 17 `defaultSimScenarios()`, 10 seeds.

**Result (gospa_mean / lifetime_ratio).**
- **Shore clutter (purpose) — dominates:** shore_clutter_open 9.90 / nearshore 6.95 vs adapt 73.8/73.5, MHT 76.3/75.8; card_err ~0 vs +27/+29.
- **parallel_lanes_dense — best:** 14.33 vs adapt 14.70, MHT 17.74.
- **Clean geometry (crossing/overtaking/head_on/convoy/crossing_30-90/clock_skew/speed_change/crossing_dropout):** bundle_land ≈ MHT, marginally behind adapt (~1–2% gospa; life 0.975 vs adapt ~0.999). No regression vs canonical.
- **non_cooperative:** bundle_land == adapt (16.94), both beat MHT (18.59) on gospa (all low lifetime — bearing-only).
- **dense_clutter — REGRESSES:** gospa **16.72 vs MHT 12.42 / adapt 13.61**; lifetime **0.639 vs 0.925 / 0.823**; card_err −0.52 (drops real targets).

**Why dense_clutter regresses — CORRECTED (see correction block below).** The
bundle_land vs adapt comparison above is CONFOUNDED: those two configs differ in
FOUR flags (dedup_miss_pd, source_aware_identity, birth_existence_target,
min_new_bernoulli_existence), so the dense_clutter regression cannot be
attributed to the miss-math from this table. The original claim here ("correct
math removed the brake → real targets are dropped") was wrong on the mechanism.

**Gate-1 verdict (unchanged, observation-level).** `bundle_land` is
**workload-specific, not a universal default**: best-in-class for coastal/
shore-clutter operation and ≈ MHT on clean geometry, but on `dense_clutter`
(uniform-Poisson, no coastline → land inert) it measures gospa 16.72 vs MHT
12.42 / adapt 13.61, lifetime 0.639. Recommendation stands: recommended config
for **coastal / near-shore** deployments, NOT the general default PMBM (which
remains `adapt`). The real-data confidence question (Gate 2: error bars on
single-seed replays) is still open.

### CORRECTION (isolated experiment — flip ONLY `dedup_miss_pd` on adapt)

The Gate-1 attribution above was confounded. An isolation (adapt vs adapt with
only `dedup_miss_pd` flipped, everything else identical, 10 seeds) gives the
true miss-math effect:

| scenario | broken (non-dedup) | correct (dedup) |
|---|---|---|
| crossing (clean) | gospa 10.18, false 3.5, life 0.999 | 10.20, false 4.0, life 1.000 — identical |
| dense_clutter | gospa 13.61, false 38, life 0.823 | gospa 14.94, false 93.5, life **0.874** |
| shore_clutter_open (P_D≈0.9, no land) | gospa 73.82, card +26.71 | 73.94, card +26.80 — identical |

Corrected conclusions:
1. **The isolated miss-math effect on dense_clutter is modest** (gospa +1.3,
   false 38→93.5) and lifetime *IMPROVES* (0.823→0.874) — correct math does NOT
   drop real targets here; it admits more uniform clutter (more false mass).
   `bundle_land`'s larger dense_clutter regression (16.72 / life 0.639) is mostly
   its OTHER flags, not the miss-math.
2. **The broken math does NOT suppress shore clutter in general.** On synthetic
   shore (high P_D, fixed) broken == correct, both over-count +26.7. There is no
   "broken math accidentally fixes shore clutter."
3. **The broken math acts ONLY in the miss branch** (`compute_miss_pD`,
   PmbmTracker.cpp:608–633: legacy path multiplies (1−pD) over every return →
   oversized miss penalty). So it only bites tracks that are frequently MISSED.
   That regime is set by the detection rate: high rate (synthetic shore 0.9) →
   rarely missed → broken==correct; low rate (philos radar ~0.07) or transient
   sources (uniform clutter) → missed most scans → broken's oversized penalty
   dominates. The synthetic-shore identical result is the direct proof.
4. So the broken math suppresses ONE property — low detection-persistence —
   which philos shore (low P_D) and uniform clutter both have, but high-P_D
   synthetic shore does not. The land prior is the orthogonal, persistence-
   agnostic spatial brake (kills on-land births at any P_D). They overlap only
   on philos shore.

## 2026-07-01 — Root cause of open-sea missed targets → general coastal config `imm_cv_ct_pmbm_land`

**Question (user):** `imm_cv_ct_pmbm_bundle_land` wins on shore/philos but DROPS
real targets in open-sea UNIFORM clutter (`dense_clutter` lifetime 0.639 vs MHT
0.925), which disqualifies it as a single all-conditions config. Why are targets
missed in open-sea noise, and can one config hold targets everywhere?

**Method:** single-knob isolation off `adapt` on `dense_clutter` (10 seeds) +
code-path mechanism read + a fix sweep incl. philos. The diagnostic test was
temporary (removed); numbers reproduce via the ablations below.

### Isolation — which of bundle's 4 knobs drops targets (`dense_clutter`, 10 seeds)

| config (single knob off adapt) | gospa | g_missed | lifetime | card_err |
|---|---|---|---|---|
| MHT (ref) | 12.42 | 34.5 | 0.925 | +0.07 |
| adapt | 13.61 | 76.5 | 0.823 | −0.19 |
| adapt + `birth_existence_target=0.1` | 15.73 | **170.5** | **0.590** | −0.745 |
| adapt + `source_aware_identity` | 13.61 | 76.5 | 0.823 | −0.19  (byte-identical → inert) |
| adapt + `min_new_bernoulli_existence=0.1` | 13.61 | 76.5 | 0.823 | −0.19  (byte-identical → inert) |
| adapt + `dedup_miss_pd` | 14.94 | 66.0 | **0.874** | +0.14 |
| bundle (all 4) | 16.72 | 171.5 | 0.639 | −0.52 |

**Root cause = `birth_existence_target=0.1`, ALONE** (0.823→0.590; worse than
the full bundle). It sets r_new ≡ 0.1 for EVERY birth via
λ_birth=(r*/(1−r*))·λ_z, independent of λ_C (PmbmTracker.cpp:478-485). Open-sea
uniform clutter has a higher λ_C than philos, so adapt would naturally birth a
real re-acquisition at r≈0.231; the pin LOWERS it to the emit floor
(`output_existence_floor` 0.1) with zero headroom, so one miss crushes it below
floor and the track fragments (birth→miss→re-birth churn). It is re-ACQUISITION
starvation, compounded by the K=1 GNN hard-commit repeatedly handing the real
target's measurement to a gate-closer clutter return. The other two non-dedup
knobs are provably INERT here (no identity signal in the scene; the 0.1 gate
never bites r_new pinned at 0.1). Mechanism cross-checked by a 5-agent read of
the birth / misdetection / assignment / metric paths.

### Fix sweep — land model alone, NO birth brake (10-seed synthetic + single-seed philos)

| scenario (metric) | MHT | adapt | bundle_land | **adapt+land (NEW)** | adapt+dedup+land |
|---|---|---|---|---|---|
| dense_clutter lifetime | 0.925 | 0.823 | 0.639 | **0.823** | 0.874 |
| dense_clutter gospa | 12.42 | 13.61 | 16.72 | **13.61** | 14.94 |
| shore_open card_err | +28.9 | +26.7 | −0.05 | **0.000** | 0.000 |
| shore_open gospa | 76.3 | 73.8 | 9.90 | **9.77** | 9.77 |
| shore_near card_err | +28.9 | +26.7 | −0.025 | **0.000** | 0.000 |
| philos gospa | 69.4 | 82.6 | 59.5 | **63.1** | 113.2 |
| philos card_err | +8.1 | +17.5 | −2.95 | **+3.95** | +48.1 |
| philos lifetime | 0.313 | 0.369 | **0.030** | **0.369** | 0.387 |
| crossing lifetime | 0.975 | 0.999 | 0.975 | **0.999** | 1.000 |

Conclusions:
1. **The shore win is 100% the land model, not `birth_existence_target`.**
   `adapt+land` matches/beats bundle_land on shore (card 0.000, gospa 9.77)
   WITHOUT the birth brake.
2. **`adapt+land` is the general coastal config.** It restores open-sea
   lifetime to adapt's 0.823 (fixing bundle_land's 0.639), repairs bundle_land's
   catastrophic philos lifetime (0.030→0.369), and posts the best HONEST philos
   gospa measured (63.1; card +3.95 — beats MHT 69.4 and adapt 82.6). SAFE BY
   CONSTRUCTION: land is inert without a coastline → byte-identical to adapt on
   every non-shore scenario (uniform clutter, autoferry, clean geometry).
3. **`dedup_miss_pd` is a philos landmine — do NOT ship it universally.** The
   dedup ("correct") miss math helps open-sea (0.823→0.874) but EXPLODES philos
   over-count (card +17.5→+48 WITH land, +112 without): on low-P_D philos the
   legacy per-return miss penalty is the load-bearing brake on phantom
   existence. bundle_land only "survived" dedup because birth_existence_target +
   land clamped the phantoms — at the cost of the 0.030 lifetime. A universal
   config keeps the legacy miss math.
4. **Residual, structural (NOT a knob):** open-sea lifetime 0.823 still trails
   MHT 0.925. That gap is present in plain adapt and is the K=1 GNN
   winner-take-all per-scan commitment (`adaptive_k_best` off, K=1): a clutter
   return inside the gate pulls the target's state off; MHT's N-scan deferral
   survives. Closing it needs a PDA-style soft detected-branch update, not a
   config value (raising K in the flat rep regresses anchored scenarios — see
   the adaptive_k_best notes above). Tracked follow-up.

**Shipped:** `imm_cv_ct_pmbm_land` (adapt + land prior only). Recommended as the
general coastal/all-conditions PMBM config, superseding `imm_cv_ct_pmbm_bundle_land`
(retained as an ablation documenting the birth-brake failure mode). The clutter
map is NOT part of the fix: it only addresses persistent SPATIAL clutter (which
the land prior already covers when a coastline exists) and does nothing for
open-sea uniform noise; it is also inert under PMBM as wired (observe() never
called). Parked.

## 2026-07-01 — Stage 1b spike: PMBM clutter-map feed measured (philos win, dense-clutter regression)

Wired PMBM to feed `detection_model_->observe()` after each scan (new
`PmbmTracker::Config::feed_clutter_map`, default off → bit-identical; commit
2457951 + review nits b9e5231), mirroring MhtTracker's producer — labels each
return with `1 − r` from the dominant post-prune hypothesis. This makes a wrapped
`ClutterMapSensorDetectionModel` finally adapt under PMBM (it was inert — PMBM
never called `observe()`). A/B harness: `tests/benchmark/test_philos_cluttermap_ab.cpp`.
Baseline A = `imm_cv_ct_pmbm_land`; B = A + `use_clutter_map` + `feed_clutter_map`.

Results (A → B):
- **philos (WIN):** card_err_mean +3.95 → **−3.2**; gospa_false 2440 → **1030**
  (−58%); gospa_mean 63.1 → **51.9** (−18%); gospa_p95 86 → 62; id_switches
  0.087 → 0; gospa_missed 1650 → 1670 (flat); lifetime_ratio 0.369 → 0.364
  (flat). **New best-honest philos** — beats MHT (69.4) and land-only (63.1),
  no wrong-math crutch. Mild over-suppression (card_err overshoots to −3.2, a
  slight under-count).
- **crossing_90 / parallel_lanes_dense / shore_clutter_nearshore:**
  **byte-identical** — the clutter map is inert (no persistent *unclaimed*
  structure to learn; near-shore clutter is already handled by the land model).
- **dense_clutter (REGRESSION):** lifetime_ratio 0.90 → **0.26**; gospa_missed
  39 → **296**; gospa_mean 12.2 → 18.0 (+48%). gospa_false 34 → 5 (fewer false,
  but at catastrophic cost). On *uniform* clutter, a low-r real target's returns
  get labeled `1 − r` ≈ high → feed the map → λ_C rises *at the target* → its
  births/updates are suppressed → r drops further → death spiral.

**Conclusion.** The mechanism is spatially selective: it correctly suppresses
clutter that is spatially *separate* from real targets (philos: fixed structures
vs vessels) but harms clutter *co-located* with targets (uniform `dense_clutter`).
So the raw clutter-map feed is **opt-in coastal, NOT universal** — same shape as
the land/bundle configs. **The honest Stage 1b layer must add a
persistence/confidence gate** (suppress only cells consistently occupied over
many scans AND spatially concentrated); uniform clutter never crosses that bar,
so the gate should keep the philos win without the dense-clutter loss. This is
also strong empirical validation that a live static-occupancy layer — not charts
(see the coverage entry below) — is the right lever for the philos over-count.
Next: build the honest geodetic occupancy layer with the persistence gate
(Stage 1b-ii) and re-measure that dense_clutter is clean.

## 2026-07-01 — Charts vs philos: chart-driven suppression is a partial lever (measured)

Parsed NOAA S-57 ENC cells for Boston Harbor (US5BOSCC/CD) were provided in
`charts/` (2,635 surface-breaking obstacles + 379 land features; export
`charts/export_obstacles.py`, analysis `charts/ANALYSIS.md`). Measured how much
of the philos persistent radar structure the chart actually explains, to decide
whether charts can fix the philos PMBM over-count. Script + map:
`charts/philos_chart_coverage.{py,png}`.

Method: projected radar plots from all 7 philos scenarios (21,647 plots) to world
coordinates (loader convention `world_bearing = heading + az_body`; registration
verified — mean radar-vs-chart offset only **~10 m**). Kept persistent
fixed-structure cells (seen across ≥2 passes or spanning a whole replay, >75 m
from any AIS vessel) = **1,727 "expected obstacle" cells**. Matched against the
chart geometries (densified to ~8 m point clouds).

Findings:
- **Coverage (obstacles ∪ shoreline):** only **36.5% of cells / 28.3% of returns**
  within 50 m of a charted feature (44.5% / 35.2% at 75 m). Discrete obstacles
  alone 34.5% @50m; shoreline alone 28.2%.
- **The strongest clusters — the actual over-count drivers — are the LEAST
  charted.** Top-100 by return count: 13% within 50 m; median distance to any
  chart feature **232 m**. Top-50: 10%, median 281 m.
- **Not anchored vessels either:** 0% of the top-100 strong clusters fall inside a
  charted anchorage/mooring/berth area (`ACHARE`/`ACHBRT`/`BERTHS`/`SMCFAC`/
  `HRBFAC`); only 5.2% of all expected cells. 13–25% sit in fairways; they cluster
  near the own-ship lane (median 180 m) → most consistent with near-field /
  own-ship-lane clutter and fairway traffic, NOT chartable static objects.
- **Chart extraction is complete:** audited all 61 ENC layers via GDAL; every
  fixed-structure / underwater-hazard / aid class is already exported. The only
  unextracted content is bathymetry (`DEPCNT`/`DEPARE`/`SOUNDG`/`DRGARE`) —
  grounding context, not radar clutter — and area layers (anchorages, tested
  above; fairways/restricted). Nothing more to squeeze for the clutter problem.

Conclusion: **the charts are a real but PARTIAL lever (~⅓ of the persistent
structure, the near-shore piers/seawalls/land edge). The dominant philos
over-count drivers are mid-water/fairway/own-ship-lane clutter that no chart
layer contains.** Hard empirical justification that the real philos lever is
**live static-occupancy (Stage 1b / Stage 2)**, not the chart. The charts remain
valuable as real `StaticObstacle`/coastline ground-truth for validating Stage 1a
correctness and the future extended-structure work — just not as a philos
over-count fix. The charted-suppression E2E measurement is therefore
deprioritised (it would confirm this predictable partial result).

## 2026-07-01 — Static-obstacle Stage 1a shipped [Cl-3 side capability]

**What shipped.** The charted-static-obstacle branch (Stage 1a per ADR 0002 and
plan `docs/superpowers/plans/2026-07-01-static-obstacle-stage1.md`):

- `StaticObstacle` type (S-57/S-101-aligned: CATOBS/WATLEV/VALSOU/depth/lit/
  AtoN realism; geodetic position + footprint/keep-clear/uncertainty radii).
- `StaticObstacleModel`: geodetic→ENU cache; `birthSuppression(enu_xy)` ramp
  (`c = 1.0` inside `R_hard = footprint + uncertainty`; linear from `soft_max = 0.9`
  to 0 across the keep-clear buffer; 0 beyond; max over all obstacles).
- `IStaticObstacleModel` port + `PmbmTracker::setStaticObstacleModel`. The PMBM
  `birthScale` now combines land and static-obstacle priors multiplicatively:
  `scale = (1 − c_land) · (1 − c_static)`, with a hard-drop when either prior
  exceeds its gate (default 0.95).
- `StaticHazardOutput` + `staticHazardId` + `toStaticHazardOutput`.
- `StaticHazardEvaluator`: keep-clear proximity alarm per (own-ship × obstacle)
  with entry/exit hysteresis. NOT a CPA — a static range check; no velocity.
- `GeoJsonStaticObstacle` adapter (GeoJSON → `StaticObstacle` list).
- Config knob `use_static_obstacle_model` (default `false`); bench sweep config.
- Integration test: vessel transits through the keep-clear buffer and is still
  tracked; phantom birth at the obstacle centre is suppressed.

**Safe-by-construction guarantee.** With `use_static_obstacle_model = false`
(the default) or no model wired, `c_static = 0` and `birthScale` reduces to
`(1 − c_land)` — the output is **bit-identical** to the pre-Stage-1 baseline
on every existing scenario. Enabling the obstacle model with an empty obstacle
list is also bit-identical.

**Soft/hard gate design.** The hard gate fires only in the footprint interior
(`c = 1.0 > 0.95`), not in the keep-clear buffer (`c ≤ 0.9 < 0.95`). This is
the **anchored-vessel protection**: a real vessel passing through the keep-clear
ring can birth and confirm through the soft ramp; only a return that is
physically inside the structure is hard-dropped.

**No A/B benchmark measurement yet.** There is no measured GOSPA / OSPA
improvement to report. None of the current test fixtures (AutoFerry, philos)
contains charted static hazards — the birth-prior effect is therefore not yet
exercised end-to-end on real data. The correct next step is a fixture with known
charted obstacles (rocks/buoys at known positions), confirmed vessel tracks that
pass close, and a before/after GOSPA comparison. Do NOT interpret the absence
of a measured delta as "no improvement" — the improvement is structural (phantom
track suppression near charted hazards) but has not been measured yet.

## 2026-07-01 — philos radar reality: the over-count is static infrastructure (raw-radar check)

Investigated the philos PMBM over-count against the RAW radar (not the AIS-only
truth), by dumping the plots through the real loader (body-frame → ENU →
geodetic) and analysing in Python. Findings:

- **Provenance:** `radar_plots.csv` is RAW PLOTS from a custom offline chain
  (`extract_radar.py`: intensity threshold ≥64 → range-gate 15–2000 m → DBSCAN
  cluster of the `radar_pcd` point clouds → one plot per cluster). NOT ARPA
  tracks — no track id/course/speed; ~10 plots/sweep.
- **Near-field, barely overlaps the targets:** all 1,962 returns are ≤ 976 m
  from own-ship (the 2000 m gate never binds — returns fade on their own).
  **Only 1 of the 23 AIS truth vessels is within radar range** (mmsi 367074170,
  77 m; 19 returns on it, closest 2 m). The other 22 are 1.2–15.8 km away.
- **The rest is static structure:** the ~1,940 non-AIS returns form a full ring
  of persistent, extended, fixed returns (`n_cells` up to 6181; straight-line
  features). Persistence: 288 of 545 clutter cells recur in ≥3 sweeps over 20 s.
- **Motion test:** greedy tracklet linking flagged 58 "coherent" tracks, but ALL
  at 12–86 m/s (impossible for boats) — artifacts of the linker chaining returns
  *along* fixed piers. A tightened detector (1–12 m/s, coherent, time-monotonic,
  ≥8 pts / ≥8 s) found **0** non-AIS moving boats.

Implications: (1) philos is a **clutter-rejection / false-positive** test — a
realistic and valuable one — not a radar+AIS fusion test (radar and 22/23
targets do not overlap). Read its over-count as clutter-rejection, not fusion
quality. (2) The over-count we suppress is (to the limit this 20 s clip can
show) real **fixed infrastructure**, not real boats being deleted — caveat: a
sub-1 m/s moored/drifting boat is indistinguishable from a structure in 20 s.
(3) This motivated the vessel-vs-environment scope decision — see **ADR 0002**
(track static vessels; handle fixed infrastructure in a separate static-obstacle
branch) and design spec §14.10. Diagnostic scripts were scratch-only (not
committed); `tests/replay/test_philos_dump.cpp` was a temporary dumper.

## 2026-07-02 — PDA soft detected-branch update: AutoFerry real-data A/B → NOT promoted (regime-split)

The promotion-to-default gate for `imm_cv_ct_pmbm_land_pda` (PDA soft
detected-branch update, commit 68c845e). Sim + philos last turn validated the
mechanism cleanly (dense_clutter lifetime 0.823→0.847, over-count down, philos
flat, flag-off byte-identical). This is the real-data reality check.

Command: `navtracker_bench_baseline --config-filter imm_cv_ct_pmbm_land
--scenario-filter autoferry` → A = `imm_cv_ct_pmbm_land`, B =
`imm_cv_ct_pmbm_land_pda`, over all 18 AutoFerry replays (9 canonical + 9
anchored). Deterministic replays (seed 0); the per-scenario spread across the
nine segments is the real-data error bar. Data:
`docs/baselines/2026-07-02_autoferry_pda_ab.csv`; analysis:
`docs/baselines/2026-07-02_autoferry_pda_ab.md`.

**Verdict: DO NOT promote. Keep opt-in.** The result is **regime-split**:

- **Open-water (env 1, scenarios 2–6, n=5) = mild win** — the exact regime PDA
  targets (open-sea K=1 gap). gospa_missed −3.5, gospa_mean 17.69→17.41,
  id_switches 7.4→6.3, and **pos_rmse lower on all 5** (13.51→12.74 m). Matches
  design + sim. No open-water regression.
- **Anchored (all 9) = flat** (lifetime 0.921→0.9203, card_err −0.001,
  gospa_false +0.05, id_switches +0). The anchored-scenario regression that
  disqualified "just raise K" is **not** tripped — the one hard gate passes.
  (Anchored tracks are well-established; in-gate returns already claimed ⇒
  pool≈1 ⇒ reduces to the hard update, as designed.)
- **Urban channel (env 2, scenarios 13/16/17/22, n=4) = mild regression** —
  gospa_mean +0.70 (4/4 worse), **pos_rmse +3.2 m / +20 % (4/4 worse)**,
  gospa_false +9.4 (3/4 worse; scenario16 +34), id_switches +1.4. Unclaimed
  structured **shore/dock clutter** enters the PDA pool and pulls tracks toward
  it. The sim harbor over-count *drop* (a large target's own hull returns
  pooling constructively) did **not** generalise to real urban shore clutter,
  which instead adds false pull.
- **Net canonical (n=9)** = wash / slightly negative on accuracy (gospa_mean
  +0.15, ospa +4.0, pos_rmse +0.99), lifetime marginally +0.0038 — the urban
  regression roughly cancels the open-water gain.

**Caveat (matters):** AutoFerry ships **no coastline**, so the land mask is
inert (land == plain `adapt` for both configs). This A/B is therefore **PDA in
isolation, no shore suppression on the pool** — a pessimistic view for a charted
coastal deployment but a fair one for the chartless general/open-water case the
default must also serve.

**Methodology note:** this is the sim-primary / real-reality-check split doing
its job — the real replay caught model-matched optimism (the extended-target
over-count drop was a sim artefact). We do not ship on sim alone.

**Principled next step (blocks promotion):** land/coastline-aware PDA pool —
exclude returns inside the ADR 0001 land-clutter zone from the β pool so PDA
softens against *water* clutter only; expected to keep the open-water win and
remove the urban regression. Re-run this exact A/B with a coastline wired for
the urban scenarios to confirm. Secondary (smaller, after): β₀ miss-term
variant; `pda_soft_detected_branch_on_confirmed_only`. `imm_cv_ct_pmbm_land`
stays the recommended default; `imm_cv_ct_pmbm_land_pda` stays opt-in.

## 2026-07-02 — Land-aware PDA pool (`pda_pool_excludes_land`): built + unit-proven + safe, but BENCH-INERT (root-caused)

Follow-up to the AutoFerry regime-split above: the plain PDA pool wins open water
but regresses urban channels because it admits **unclaimed shore/dock clutter**
into the β pool. Fix: drop non-winner returns whose `ILandModel::clutterPrior`
(same signed-shoreline prior as land birth suppression) exceeds
`pda_pool_land_clutter_gate` (default 0.5 = waterline). The winner is always kept
(hard assignment unchanged); the query point is the per-cell post-update position
`updated[i][j].mean.head<2>()` (robust for bearing-only). Off / no land model →
byte-identical. Config `imm_cv_ct_pmbm_land_pda_wateronly` = `_land_pda` + flag.
Code: `core/pmbm/PmbmTracker.cpp` pool loop; TDD `PmbmPdaLandAwarePool`
(`ShoreClutterExcludedFromPool` RED→GREEN: a coastline-flagged non-winner shore
return is excluded so the update reduces to hard; `WaterClutterStaysInPool`
control). Full suite green (895 tests); docs pmbm-design §11.5 + learning ch.12.

**Finding: the mechanism is inert on every current bench fixture, and this is
correct-by-diagnosis, not a bug.** A/B `_land_pda` vs `_wateronly` over the full
42-scenario matrix: **byte-identical on all 42** (accuracy metrics). A gate=0.0
diagnostic (exclude *any* non-open-water return) on the coastline-active
scenarios (philos, philos_radartruth, shore_clutter_open/nearshore, harbor_*)
is **still byte-identical**. Root cause: the exclusion can only bite when the PDA
pool holds a non-winner **gated + unclaimed + shore** return, and no fixture has
all four:
- Coastline fixtures (philos/shore/harbor): the pool is already ≈{winner}. In
  shore_clutter_nearshore the vessel runs x∈[−500,−260] while the pier clutter
  sits x∈[−20,20] — never in the vessel's gate, so nothing to pool (gate=0 proves
  it, ruling out "gate too high").
- The one regime where the plain pool *does* pull onto shore clutter (AutoFerry
  urban) ships **no coastline** → the land model can't flag those returns.

So the plain PDA pool's shore-clutter pull and the land model live in disjoint
fixtures. The refinement is justified (a charted urban deployment WOULD have both:
birth suppression removes shore returns from *births* but not from the *scan*, so
they stay gated+unclaimed and poolable) but unmeasurable here. It ships as a
safe, unit-proven insurance refinement; kept opt-in via `_wateronly`.

**Validation gate (unchanged conclusion, sharper target):** a controlled sim
fixture where a vessel **establishes offshore then transits into a near-shore
dock-clutter field** (established track survives the ADR-0001 no-birth band; the
in-gate dock returns are coastline-flagged) — plain `_land_pda` should pull the
track ashore, `_wateronly` should hold it on truth. Or drape a synthetic
coastline over the AutoFerry urban channels and re-run land/`_land_pda`/
`_wateronly`. Until one exists, land-aware pooling stays proven-safe-but-
unmeasured. Baseline: `docs/baselines/2026-07-02_pda_landaware_ab.csv`.

## 2026-07-03 — Land-aware PDA pool: controlled fixture built → VALIDATED (10/10 seeds)

Closes the "proven-safe-but-unmeasured" gap above with a purpose-built
sim-primary fixture, `shore_clutter_transit` (`adapters/benchmark/SimScenarioRun.cpp`).
Design lessons from the failed first attempt are baked in:
- **First geometry (perpendicular transit) was too weak** — vessel establishes
  offshore then crosses toward shore; the dock only enters the gate for the last
  ~10 of 40 scans, so the pull was noise-dominated (paired pos_rmse: 6/10 seeds
  better, mean +0.36 m, sd 0.84 — could flip). Root cause: with the default 50 m
  shoreline ramp, a vessel far enough offshore to birth cleanly (d ≥ 50 m ⇒ c=0)
  is > 43 m from any c>0.5 dock return, so the dock barely gates.
- **Fix = alongshore channel + steep quay.** The vessel runs **parallel** to a
  **20 m-ramp** quay at y=478 (22 m offshore ⇒ c=0, clean births, never in the
  ADR-0001 no-birth band), with a dense line of unclaimed quay returns just
  inland at y=510 (c=0.75 ⇒ r_new≈0.025, never births ⇒ stays unclaimed), 25 m
  apart so 2–3 are in-gate EVERY scan (offset ≈ 32 m ⇒ Mahalanobis² ≈ 11 < gate
  20). Births are land-suppressed identically under both configs — the ONLY A/B
  difference is the PDA softening pool.

**Result (10 seeds, `_land_pda` vs `_wateronly`):** pos_rmse plain **17.0 m** →
wateronly **8.6 m** (Δ **+8.4 m**, paired **10/10 seeds better**, min +0.06 m);
lifetime 1.0 for both (the fix costs no track). Plain PDA is dragged toward the
quay (~doubled error); the land-aware pool holds the track at the ~8 m
measurement-limited tracking error. Contract test
`SyntheticClutterAB.LandAwarePoolResistsDockClutterPull` (8 seeds, margin 2 m).
Scenario count 22→23; config count 33 unchanged. gospa/ospa/card are noisy on
this scene (persistent quay + inland clutter → phantom over-count in BOTH), so
pos_rmse (single-truth position error) is the clean discriminator.

**Residual:** the mechanism is now proven both at unit level and on a controlled
sim fixture. The one open step before promoting `_land_pda` past opt-in is
real-data: AutoFerry urban ships no coastline, so drape a synthetic coastline
over those channels and re-run the land/`_land_pda`/`_wateronly` A/B.

## 2026-07-03 — PDA promotion gate: REAL Trondheim coastline → HOLD (do not promote)

The real-data reality check for the land-aware pool, and the promotion decision
for `imm_cv_ct_pmbm_land_pda`. Full writeup:
`docs/baselines/2026-07-03_promotion_decision.md`; baseline:
`2026-07-03_promotion_autoferry_real_coast.csv`.

**Real geometry, not hand-draped (deliberate).** AutoFerry was chartless because
the loader never set `Scenario::datum` (Sweep's `scen.datum.has_value()` guard
failed) — not merely missing a coastline. Sourced the **real Trondheim
inner-harbour coastline from OpenStreetMap** (Overpass: natural=coastline + the
Kanalen/Ravnkloløpet/Nidelva canals), assembled about the Piren datum
(LLA 63.4389029083, 10.39908278), ODbL. Validated: 100% of AutoFerry ground
truth (scenarios 2/3/13/16/17/22) falls in water. Wired the datum + coastline
onto every AutoFerry scenario (inert for non-land configs; commit cc9741a).
Fixture `tests/fixtures/autoferry/trondheim_harbor.geojson`, regen
`tools/build_autoferry_coastline.py`. A hand-drawn coast at this load-bearing
input would make the confirmation half-synthetic and could be unconsciously
fitted to the clutter — the whole point was to let real geography adjudicate.

**Result (candidate `_wateronly` = `_land_pda` + land-aware pool, vs default
`_land`):**
- **Urban (13/16/17/22): regression NOT closed.** pos_rmse `_land` 15.67 →
  `_land_pda` 18.88 → `_wateronly` **17.77 (+2.10 vs land)**; gospa +0.43. The
  land-aware pool recovers only ~⅓ of the plain-PDA regression.
- **Open-water (2–6): win retained.** pos_rmse 13.51 → 12.74 (−0.77); gospa
  −0.29. (`_land == adapt` here — coast far from the vessels; `_wateronly ==
  _land_pda` — no in-gate shore returns.)
- **Anchored (×9): flat.** gospa +0.03, lifetime −0.001.
- **philos: flat.** `_wateronly == _land_pda` (byte-identical on dense) = 63.08
  vs `_land` 63.13.

Promotion needed all four; three pass, **urban fails → HOLD.** Root cause: much
real urban-channel clutter is **in the water** (moored vessels, floating
structures, near-shore-but-offshore returns, clutterPrior < 0.5) — the land mask
cannot flag it, so land-aware pooling only removes the on-land quay share. The
loader's own detection-table comment already flagged the urban excess as
"persistent structured returns (shoreline, **moored vessels**)". The sim fixture
(on-land dock clutter) was necessary but not sufficient — it proved the mechanism
for on-land clutter; real geometry shows on-land is only part of the problem.

**Decision:** `imm_cv_ct_pmbm_land_pda` / `_wateronly` **stay opt-in**;
`imm_cv_ct_pmbm_land` remains the recommended default; the K=1 north-star item
stays "shipped (opt-in)", not promoted. The residual in-water structured-clutter
pull is an association/existence problem, not a land-mask one (β₀ miss term,
confirmed-only softening, or the live static-occupancy layer / Stage 1b) — none
promoted here. This is the sim-primary / real-reality-check split working as
intended.

## 2026-07-03 — philos camera → bearing-only fixtures (multi-sensor enablement)

Built the offline camera→bearing pipeline (`tests/fixtures/philos/
extract_camera_bearings.py`) so the radar-only philos clips carry a real EO/IR
bearing-only corroboration channel. Fixture-generation + C++ wiring proof ONLY
(the Stage 1b-ii KEEP-guard consumer is a later ticket). Detector: ultralytics
YOLO `yolov8n.pt` (v8.4.0, sha256 f59b3d83…), COCO boat class, conf 0.25, imgsz
1280, CPU, in a dedicated `.venv-cam` (no C++/Conan dependency added). The
dataset ships real intrinsics + extrinsics (`metadata/cal_files`, appendix), so
the model is intrinsics-based with one AIS-fit yaw offset per camera — better
than the ticket's linear `a+b·u` fallback.

**Calibration (ais_ferry_near center, AIS RANSAC fit vs the Frederick Nolan
ferry).** 262 correspondences → 259 inliers (98.9%); yaw_offset = **2.29°**;
held-out (30%) residual **median 0.45°, p90 1.32°** — comfortably inside the
≤2°/≤4° target. The small 2.29° confirms the philos heading behaves as
effectively true-referenced (radar world bearing matches AIS true bearing on the
~90 m ferry to ~1–6°, not the ~14° Boston declination); the fit absorbs the
residual. Left/right propagated from center via the known ±45.3° body-frame
extrinsics (σ +2° floor, boresight not AIS-validated).

**Detection counts / emission.**
- `ais_ferry_near` (240 frames/cam): center 306 / left 1 / right 729 boat
  detections → emitted center 304 + left 1 + right 725 (6 dropped no-pose).
- `sunset_cruise` (philos 2021, same vessel; 1439/1439/765 frames): center 4609
  / left 0 / right 14 (sunset glare inflates center false-positives). Center yaw
  transferred from the 2022 AIS fit; sanity check vs the labeled ferry: n=3008,
  median 2.58°, p90 6.80° (larger — cross-deployment mount + 40 m label fuzz);
  passed the lenient ≤4° transfer gate → emitted **center only** (4605 rows,
  σ≈3.5°); left/right withheld (no validation that side).
- `close_approach` (prodromos 2021): **REFUSED**, detector not run — the
  prodromos vessel ships no camera cal files (no intrinsics) and is a different
  platform; a wrong bearing is worse than none.

**C++ wiring proof.** `adapters/replay/CameraBearingCsvReader` loads the CSV to
`Bearing2D` (EoIr) measurements, composing own-ship heading at load time to the
same `atan2(dN,dE)` ENU convention radar plots use. `tests/replay/
test_camera_bearing_loader.cpp`: 6 unit tests (parse / heading composition /
value convention / wrap / no-pose drop / invalid-σ / per-camera source-id /
`canInitiateTrack==false`) + 2 skip-guarded smoke tests on ais_ferry_near —
camera-only births **0** tracks; radar+camera lands **≥1** Bearing2D update on a
radar-born track (mechanics only; no accuracy assertions — circularity rule).
Full suite **945/945 green**, determinism green.

**Contract notes.** Absence asymmetry (a detection is presence evidence; its
absence is never SUPPRESS evidence) and circularity (labels derived from the
same videos → detections are corroboration/mechanics only, never accuracy
truth) are documented at the fixture (`README.md`) and in sensor-reference §3.
All of `tests/fixtures/` is gitignored ("never committed" — multi-GB local
data), including the emitted CSVs, the detector script, `camera_bearing_geom.py`,
and `camera_bearing_calibration.json` — exactly like the existing (also-local)
`extract_section.py` / `extract_radar.py`. So the ticket's "commit the CSV" does
not apply here; the CSV would orphan from its regeneration pipeline anyway. The
**tracked drift-guard** is instead this log: the model pin above + the emitted-
CSV checksums below. Ownship/radar extraction is deterministic from the bags,
but YOLO output is only deterministic given the pinned weights + environment, so
a future ultralytics/torch bump could silently shift detections — a mismatch
against these checksums makes that drift loud.

| Emitted fixture | rows | sha256 |
|---|---|---|
| `out/ais_ferry_near/camera_bearings.csv` | 1030 | `db3159b19eaf4209554b7bc25986780717e4271b9bb9a4d9d665a6d7927a8081` |
| `out/sunset_cruise/camera_bearings.csv` | 4605 | `865eb845046a78c942b67b2c9d9fc2062eb023ce82e931a154f1d17d25a99bc6` |

The only git-committed deliverables are the C++ loader
(`adapters/replay/CameraBearingCsvReader.{hpp,cpp}`) + its tests
(`tests/replay/test_camera_bearing_loader.cpp`) + the CMakeLists wiring; the
skip-guarded smoke test tolerates the fixtures' absence on a fresh clone.

## 2026-07-07 — Clutter/birth campaign CLOSED: measured negative at the birth channel + contract-boundary finding

The increment-8 redirect ("reduce PMBM dense-scene over-count via a clutter/birth
model") is **closed as a measured negative.** Design-first campaign
(`docs/superpowers/plans/2026-07-06-clutter-birth-campaign-{ticket,design}.md`),
branch `clutter-birth-campaign`. Phase 0 (backlog #21 band guard) already on master
(`fb7782c`). **Zero implementation waste**: the binding entry probe killed a
structurally-doomed build before it started. This is the cheapest negative the
project has bought; the design-first + binding-entry-probe shape is now the template
for research campaigns.

**Durable result 1 — the `λ_C`-cancellation invariant (root cause of the "cmap inert
under PMBM" puzzle).** Under `adaptive_birth`, birth existence is
`r_new = λ_birth/(λ_birth+λ_C)`. With `birth_existence_target > 0`
(`imm_cv_ct_pmbm_coverage_land` and all `_bundle*`/`_coverage`),
`λ_birth = (r*/(1−r*))·λ_C` ⇒ **`r_new = r*` exactly, independent of `λ_C`**
(`PmbmTracker.cpp:500-507,1082-1083`). So a spatial/per-sensor/count-adaptive `λ_C`
is *cancelled* on the deployed config — the shipped `ClutterMapSensorDetectionModel`
read path is wired but inert there. **Any clutter lever must ride `birthScale`
(the land/static-obstacle birth-prior channel), never `λ_C`.** Recorded as a named
INVARIANT in `pmbm-design.md §3.2.2`.

**Durable result 2 — the birth channel cannot reach confirmed phantoms (§5.0 probe).**
`tests/benchmark/test_clutter_burst_birth_confirm_probe.cpp` (permanent regression
test; skips w/o `SIMMS_DIR`). Faithful to the instrument: the probe drives
`imm_cv_ct_pmbm_coverage_land` with the Sweep wiring and the real bench on the same
cell gives `card_err_mean = 3.48253` — bit-for-bit the pinned +3.48 (fixtures
sha256-verified). Findings:
- **Confirmed count jumps 2 → 15 in ONE radar scan** at burst onset (t=120 s); 12
  burst-region ids, all confirmed ≤2 scans, none later — the region saturates at
  scan 1 (`smart_birth_skip`), so no turnover, and the dense disk re-detects them
  every scan → they never miss/die → persist through 60 % of the post-burst run.
- Over-count split: pre-burst background **0.85** phantom (the only birth-reachable,
  turnover-y part); the rest (**~2.69**) is burst + its decaying tail, unreachable.
  **A perfect birth fix floors `card_err` at ~2.69 — still above MHT's +2.51**, far
  from the +0.9 ideal.
- Why the whole birth *channel* fails (both candidates): (1) a learned prior sees a
  scan's returns only post-scan → can't suppress the t=120 first wave (kills spatial
  candidate A); (2) saturation → no later births to suppress; (3) channel-reach wall
  → can't touch confirmed phantoms; (4) the count candidate B is not saved by
  same-scan timing — a global count can't tell a concentrated 150 m disk from diffuse
  compound-K of equal count, and a correct negative-binomial finds the burst's high
  count *unsurprising*.

**Durable result 3 — scenario-honesty / contract-boundary finding (arbiter ruling).**
`sim_ms_clutter_burst`'s dominant mass is the persistent 150 m, 25-plot/scan disk —
a duplicate-cloud *pre-extraction* shape that the 2026-07-06 extraction-boundary
ruling assigns to **upstream** (radar API / commercial extractor). The deployed
tracker is contractually entitled to plot-level input, and the burst as simulated
would largely not survive a competent upstream extractor. So the discriminator,
built in good faith, **conflated an upstream problem (the burst — dominant in the
metric) with the genuine tracker-level problem (the over-dispersed *diffuse*
background — the 0.85 pre-burst phantoms in sim; HAXR's ~48.8).** The controlled
instrument was pointed mostly at the wrong layer. `clutter_burst` **stays** (it now
measures resilience to contract-violating input — the tracker survives it with
bounded over-count) but is **no longer billed as the tracker-level clutter
discriminator**; a post-extraction-representative scenario (point-like false plots,
over-dispersed counts, no duplicate disks) is the pull-based follow-up if
tracker-level clutter work re-opens. See the sim-battery doc scenario-honesty note.

**Parked with triggers (not built):** (i) existence-side clutter penalty and (ii)
non-Poisson clutter cardinality in the *update* — both deep hot-path changes whose
motivating mass just moved upstream; (i) would put ADR-0002 over-delete risk onto
*confirmed* tracks (the most dangerous place). **Trigger:** revisit only if
post-water real data (with the real upstream extractor in place) shows
confirmed-phantom persistence in spatially-concentrated clutter that upstream can't
fix. Recorded in `improvement-backlog.md`; learning `13-clutter-and-detection.md §10`
stays "not picked" with the reason upgraded from *judged* to *measured*.

**Net:** the increment-8 dense-harbor over-count redirect is closed **both ways** —
suppression-side (increment 8: occupancy persistence, <3 % on HAXR) and birth-side
(this campaign: structurally insufficient, floor +2.69 > MHT +2.51). What remains of
the over-count belongs to **upstream extraction** and to whatever the water test
teaches. Durable contributions carried forward: the `λ_C`-cancellation invariant,
the `birthScale`-not-`λ_C` channel map, the minefield analysis (design note §1.4-1.5),
the §5.0 probe as a permanent regression test, and Phase 0 (backlog #21) on master.
## 2026-07-08 — D10 Global Fishing Watch anchorages: license NO-GO (c) for our (commercial) context; D3 not replaced [Cl-3 feasibility; desk check, no download]

Feasibility-only assessment of the GFW anchorage database + Events API (data-
expansion item D10, pre-water item 13). Verdict: **NO-GO** for navtracker's
commercial (TKMS) context — decisive on license alone. **Desk check only: no
registration, no download, no data pulled**; the Step-0 gate hit classification
**(c) not usable**, so execution stopped before Step 1 per the ticket. Report:
`docs/baselines/2026-07-08_d10_gfw_anchorages.md`.

**License — (c), decisive.** GFW **data products** are **CC BY-NC 4.0**
(NonCommercial): ToU — "data products ... are provided for and subject to
non-commercial use in accordance with the Creative Commons Attribution
Non-Commercial 4.0 license"; "provided for Non-Commercial use only ... for
commercial purposes, please contact us." CC BY-NC 4.0 — NonCommercial = "not
primarily intended for or directed towards commercial advantage." The **Events
API** is likewise "only available for non-commercial purposes" and requires
registration + a token + *agreeing to* the non-commercial terms (an independent
registration-wall blocker — a commercial entity cannot truthfully accept). This
is the **same NonCommercial ground that killed D7 MOANA**; GFW is lighter (CC
BY-NC, **no ShareAlike**) but the NonCommercial term alone bars product-directed
use — including "research-side statistics that inform our design", since that is
still directed toward commercial advantage (so classification (b) does not
survive either). **Apache-2.0 red herring ruled out:** Apache covers the GFW
pipeline *code* (`anchorages_pipeline` repo), not the *data product*; the ToU
CC-BY-NC controls the data.

**Boston sanity anchor (not measured; expected MISS).** No download, so the
video-verified cluster at ≈42.3585 N / −71.0464 (largest `KEEP_INCOV_UNCHARTED`
driver) was not checked against GFW. On paper: a **likely miss**, because GFW
needs ≥20 **AIS-transmitting** vessels and our cluster is AIS-dark small
recreational craft. The blind spot is the finding: a GFW anchorage layer is dark
over exactly the small-craft fields that generate our hardest KEEP cases.

**D3 — not replaced, not shortened.** Per-statistic (on paper, moot under
license): anchorage *locations* covered (coarse ~0.5 km S2 cells, commercial
anchorages only); *dwell* derivable from visit events; *transitions* partially
derivable but AIS-derived (the veto's existing signal); **watch-circle swing
radius NOT covered at any resolution** — and that is the statistic D3 most needs.
GFW pre-computes what D3 needed least, omits what it needed most. **MarineCadastre
(U.S. public-domain AIS) stays the lawful, necessary D3 route** for watch-circle
+ per-vessel dwell.

**KEEP-side prior — use ENC charts, not GFW.** GFW anchorage clusters as a
"known anchorage → bias KEEP" prior: low fairway-FP risk by construction (≥20
vessels *stop* there) but coarse (~500 m blobs), AIS-blind to small craft, and
license-barred. The right source for the prior is the **official ENC / S-57
charted anchorage-area polygon (`ACHARE`, berths `ACHBRT`)** — authoritative,
surveyed, commercially clean, already in the chart-corroboration substrate. **Do
not wire a GFW-derived KEEP prior.** No code changed, no prior wired.

**Net.** D10 NO-GO on license; the only lawful GFW path is a commercial grant
("please contact us") — an organizational decision for the user, not extraction.
Queue effect: D3 is **not** unblocked/shortened by D10 (MarineCadastre still
required for watch-circle), and the chart-corroboration KEEP prior should be
sourced from ENC `ACHARE`, not GFW. Sources: GFW ToU / anchorages page / API
docs; CC BY-NC 4.0 legal code; `anchorages_pipeline` (Apache-2.0 code);
D7 MOANA entry (2026-07-06).

## 2026-07-08 — [Cl-1] Cold-start Helgesen re-score: env-1 gap CLOSED by PMBM (18.62 < paper 20.37); frozen 43.4 row is stale [CHECKPOINT — no Phase 2]

Ticket `docs/superpowers/plans/2026-07-08-cl1-coldstart-ticket.md`. The last
open ❌ on the Cl-1 headline card ("beat in cold deployment without anchor")
was frozen at the **2026-06-13** `imm_cv_ct_mht` run (`gospa20m_20260613T174620Z`,
env-1 GOSPA RMS 43.4 vs paper 20.37 → ×2.1). Nobody had re-scored since the
UKF promotion and PMBM Phases 4–7. Measurement-only pass, **zero config/algorithm
change**. Worktree `cl1-coldstart-rescore` @ `7f5cd17`, autoferry fixtures
symlinked from main. Full table + provenance in
`docs/baselines/helgesen2022_reference.md` (new dated section; frozen table
untouched). CSV checksums there.

Exact commands (from worktree root):
```
./build/bench/navtracker_bench_baseline --run-id cl1_rescore_mht_20260708  --config-eq imm_cv_ct_mht       --scenario-filter autoferry_scenario --seeds 1 --out docs/baselines/
./build/bench/navtracker_bench_baseline --run-id cl1_rescore_pmbm_20260708 --config-eq imm_cv_ct_pmbm_land --scenario-filter autoferry_scenario --seeds 1 --out docs/baselines/
./build/bench/navtracker_bench_baseline --run-id cl1_drift_ekf_20260708    --config-eq imm_cv_ct_mht_ekf   --scenario-filter autoferry_scenario --seeds 1 --out docs/baselines/
```

**Phase 0 — reproduction is PARTIAL (a finding, not hidden).** Per-env GOSPA RMS:

| Stack | env-1 | env-2 |
|---|---:|---:|
| Frozen 2026-06-13 (pre-UKF EKF) | 43.4 | 33.9 |
| Current `imm_cv_ct_mht_ekf` (pre-UKF filter, ablation) | 39.42 | 33.91 |
| Current `imm_cv_ct_mht` (UKF default) | 34.37 | 28.57 |

env-2 reproduces **exactly** under the pre-UKF filter (33.91≈33.9) → its whole
drift is the **UKF flip `6106ec7`** (2026-06-20). env-1 is ~4 m lower even
under EKF (43.4→39.42, −9%) → ~44% of the env-1 drift is *non-UKF* merged bench
change (candidates: truth-sort `3ee491f`/`3aa9c58`, GOSPA decomposition
`711cf45`; exact per-commit split not bisected), the rest (−13%) is the UKF
flip. **The 43.4 row is stale; honest current MHT cold-start = 34.37/28.57.**
Table NOT silently rebased — arbiter picks the baseline.

**Phase 1 — the decision table (cold-start = no-AIS is the claim):**

| Condition | Config | env-1 | env-2 |
|---|---|---:|---:|
| no-AIS | `imm_cv_ct_mht` (UKF) | 34.37 | 28.57 |
| no-AIS | **`imm_cv_ct_pmbm_land`** | **18.62** | **17.74** |
| truth-AIS | `imm_cv_ct_mht` | 5.18 | 5.16 |
| truth-AIS | `imm_cv_ct_pmbm_land` | 3.43 | 8.94 |
| paper | Helgesen 2022 | 20.37 | 30.97 |

**PMBM cold-start env-1 = 18.62 BEATS the paper's 20.37** (env-2 17.74 ≪ 30.97).
The ×2.1 gap is closed with no tuning.

**Mechanism (free from the GOSPA decomposition, not a Phase-2 run).** The whole
MHT→PMBM env-1 win is cardinality: `imm_cv_ct_mht` over-counts (card_err +3.6…
+5.1, gospa_false 830…1070, id_switches 16…49 — the backlog-11 duplicate-track
conveyor); `imm_cv_ct_pmbm_land` holds card_err≈0 (gospa_false 63…160, ~7×
smaller, id_switches 1.5…14.5). Localization comparable; PMBM's missed
component is slightly higher (existence flickers → breaks 14–60/scenario,
lifetime 0.53–0.81), but at c=20 a break-step is a bounded miss while a
duplicate is a full false. Confirms the standing **Cl-2 #2** hypothesis: one
PMBM existence+association recursion makes the env-1 over-count moot.

**Operational trade (framed, not adjudicated).** Opposite failure modes; GOSPA
scores one and is blind to the other. PMBM: best GOSPA/pos_rmse/cardinality/
id-stability, **worst continuity** (track drops+reacquires — coincides with
backlog **#25** close-pass loss). MHT: best presence/continuity (~90% lifetime),
**worst cardinality** (duplicate/renamed tracks). The paper is scored on GOSPA
and PMBM beats it; continuity is a separate deployment axis.

**Verdict (a) — implementer read; arbiter decides & lands north-star edit.**
Cl-1 "beat in cold deployment without anchor" ✅ on the PMBM canonical, with the
continuity trade recorded. **CHECKPOINT honored: Phase 2 (NEES-per-scenario deep
dive + sim observability control) NOT entered — awaits arbiter go.** No code
changed anywhere in this ticket.

---

## 2026-07-10 — PMBM promotion dossier (every deployment-decision number at one commit)

Full writeup + tables: `docs/baselines/2026-07-10_pmbm_promotion_dossier.md`.
MEASUREMENT ONLY (no config/core/tuning change); compiles the champion
(`imm_cv_ct_mht`) vs candidate (`imm_cv_ct_pmbm_coverage_land_ivgate`) gauntlet
at **one commit `d94471e`**, one harness state, for the canonical-tracker call
(north-star Cl-3 #3). Branch `pmbm-promotion-dossier`; commands + sha256 in the
dossier §4.

- **STOP-gate PASSED:** the Cl-1 frozen protocol reproduces to printed precision
  (mht no-AIS 34.37/28.57, pmbm_land 18.62/17.74; truth-AIS 5.18/5.16, 3.43/8.94).
  Imazu, sim_ms, and the HAXR veto 3-site table also reproduce exactly.
- **NEW finding (decision-critical):** the candidate's coverage+land stack
  **collapses on autoferry env-2** (shore-hugging urban channel): lifetime 0,
  card_err −2, gospa pinned at cutoff. Root cause = the documented <50 m
  no-birth zone (Config.cpp:1220). Isolated to the coverage/land model, **not**
  the innovation gate (plain `coverage_land` gate-OFF shows the identical
  collapse). The Cl-1 win (18.62) belongs to `pmbm_land`; the candidate is
  *better* on env-1 open water (17.44 < paper 20.37) but disqualified near-shore.
- **Candidate #25 fix reproduces Stage-2 exactly:** 6-dying-truths CPA-overlap
  loss **163 → 6 s**, total dying loss 1366 → 544 s, reacquire-new-id 45 → 10,
  id-switches ≤ 2.3 (no id-snap).
- **Gate fires 0× on real data:** philos candidate byte-identical to
  `coverage_land` on every accuracy/continuity/identity metric (KEEP safe).
- **Runtime:** champion MHT is **not realtime on radar density** — decimated
  worst-scan 1168 ms (7.9× the 148 ms interval), raw-density **timeout
  (intractable)**; candidate 30 ms decimated / 78 ms raw (reproduces the perf-arc
  PMBM figures). Harbor lifetime 0.975 yardstick holds; sim_ms fusion-vs-radar
  33.1 vs 67.2 reproduces.
- **No promotion recommendation** (per ticket) — the dossier frames the trade;
  the arbiter/user own the call and the north-star edit.

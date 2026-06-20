# HR Radar Engine — Audit & Sharpening Roadmap (June 2026)

> **Trigger:** HR Radar surfaced **206 "MISSED" vs ~6 conversions in a single day**. The product read
> ("not a strategic engine — spray-and-pray — we're calling everything a home run") is correct. This
> document separates the two tangled root causes, then lays out a phased plan to make the radar
> strategic, honestly graded, EV-aware, and more accurate.
>
> **Status:** Audit + roadmap only. No engine/runtime code is changed by this document. Implementation
> follows in subsequent PRs under the discipline in `CLAUDE.md` §7a (sanctioned engine changes).

---

## 0. Executive summary

Two distinct problems are being conflated:

1. **Accounting/funnel (why it *looks* like spray-and-pray).** Nearly every batter who makes decent
   contact gets a canonical `watch` signal, and at game-final **every still-active non-HR signal is
   stamped `called_miss`**. Ambient *tracking context* is counted as if it were a *betting pick*. The
   UI string "did not convert before the window closed" is cosmetic — **there is no PA/time window and
   no expiration clock**; "window closed" simply means the game ended. So the **206 "misses" ≈ every
   batter we ambiently watched who didn't homer**, not 206 failed bets.

2. **Model (why there's no strategic edge).** The conversion probability is a large hand-tuned
   multiplier stack that is **never calibrated against realized outcomes** and **never compared to the
   HR prop market price** (`batter_home_runs`, which we already ingest). There is no concept of
   edge/EV, and no honest measure of *lift over the ~12%/game base rate*.

**Direction (approved):** collapse the ladder to **3 tiers — Watch → Building → HR Max Window** — promote
through Watch/Building faster, **grade only the HR Max Window tier** as a real pick, **EV-gate** that
tier against the market, and **improve the underlying probability** with new stats, an explicit
hard-hit interaction term, and a closed calibration loop.

---

## 1. Audit findings (what exists today)

### 1.1 The funnel has no top-of-funnel selectivity
- `server/mlb/liveGameOrchestrator.ts` runs a **periodic roster scan** (`HR_ROSTER_SCAN_INTERVAL_MS`,
  ~lines 2809–2859) that feeds **every batter with any plate appearance** into the near-HR detector. No
  HR-likelihood pre-filter.
- `server/mlb/nearHrContact.ts` **WATCH** tier fires on `EV≥98 + LA[20–35] + dist≥350` — i.e. **any
  well-struck fly/line out**. Dynamic-state gates (`server/mlb/hrAlertEngine.ts` ~lines 201–203):
  `WATCH ≥ 0.05`, `PREPARE ≥ 0.06`, `BET_NOW ≥ 0.10` — all *per-PA*. At a ~3.3%/PA league base over
  ~4 PA, a large fraction of the slate clears 5%.
- **Consequence:** the `watch` state is *ambient context*, not a pick. That's fine — but today it is
  graded as one.

### 1.2 "MISSED" is an inflated denominator
- `server/mlb/hrRadarStateMachine.ts`: terminal `missed` is produced by a `GAME_FINAL` event on **any
  still-`active`** signal (watch/build/ready/fire). Terminal states are sticky.
- `server/storage.ts` `reconcileHrRadarAlertsForGame()` (~lines 4478–4614): at `status:"final"`, every
  live HR Radar alert whose player is **not** in the box-score HR map is stamped `called_miss`
  ("reconcile: game ended without HR for this called signal", ~line 4588).
- The humanized UI text "Signal was tracked and did not convert before the window closed"
  (~`storage.ts:5906`) is **cosmetic** — there is **no PA/time window and no expiration clock** in the
  lifecycle. A signal can decay `fire → watch` over several innings and still be counted as a miss at
  game-final.

### 1.3 The probability model is rich but uncalibrated and price-blind
- `server/mlb/hrConversionModel.ts` is a sequential multiplier stack on a `0.033`/PA base
  (handedness-blended 70/30), with **capped** components:
  - live contact (≤×2.5, ~lines 215–251), barrel (≤×1.5), contact-quality anchor (xwOBA/xSLG),
    pitcher fatigue/ERA/HR9/velo (≤×2.0), environment park/wind/temp/humidity/pressure/pitch-mix
    (≤×1.35), pregame power form, recent form, IBB "feared slugger" prior, lineup slot.
  - Final per-PA clamp `[0.005, 0.12]`, then converted to game-level **P(≥1 HR)** via a PA distribution
    and a **static calibration table** (~lines 163–178).
- **The calibration table is hand-set, not learned.** An empirical-bucket hook exists but is not
  populated from a closed feedback loop tying `convProb` → realized HR.
- **The market price is never consulted.** `batter_home_runs` exists (`server/oddsService.ts:1212`) and
  flows through the prop-edge engine (`markets.ts` / `backtestHarness.ts`), but the **HR Radar live
  track is a separate pipeline that ignores it.** No edge, no EV, no "only fire when model > market".

### 1.4 Data inventory — strong, with specific gaps
**Already ingested and usable** (`server/mlb/dataSources.ts`, `dataPullService.ts`):
- Statcast season profile: barrel%, xISO, xwOBA, HR/FB, FB%, pull%, sweet-spot%, **bat speed**, swing
  length.
- Rolling **AVG/OPS/HR-rate** (L7/L15/L30); handedness splits (HR/AB & OPS vs LHP/RHP); BvP history.
- Live per-AB contact: EV / LA / distance / per-AB xBA / barrel flag / outcome / hit-type.
- Pitcher: season + handedness (ERA, HR/9 vs LHB/RHB), recent-start fatigue, **live pitch mix & velo
  trend**, bullpen usage.
- **Handedness-aware park factors** (`PARK_FACTORS.hrLHB / hrRHB`); live + Open-Meteo weather
  (temp / wind / humidity / **pressure**). Live state: inning, outs, runners.

**Missing / referenced-but-unused / under-leveraged:**
- **Handedness park factor unused in the live model** — `hrLHB/hrRHB` exist but the environment
  multiplier uses the *generic* `hr` factor, ignoring short-porch pull effects.
- **No rolling Statcast quality** — we have rolling AVG/OPS/HR-rate but **not** rolling
  barrel%/hard-hit%/xISO (L7/L15). A hitter can be hot in OPS but cold in power.
- **No batted-ball-type weighting per AB** — a 96-EV line drive is scored like a 96-EV fly ball.
- **Bat speed ingested but unused** — `avgBatSpeed`/`avgSwingLength` feed nothing in the model.
- **No interaction term** — EV/hard-hit, xBA, launch angle, bat speed, and IBB are scored as
  *independent* components. Real-world truth is multiplicative: **a hard-hit / high-xBA ball paired with
  a favorable launch angle + high bat speed (or a feared-slugger/IBB profile) is overwhelmingly likely
  to be a HR** — the additive stacking under-rewards that co-occurrence.
- **No count/leverage feature**; **no pitcher pitch-type HR vulnerability** (we have pitch-mix %, not
  HR-per-pitch-type allowed); **market line / steam unused** as a feature; **wind-shift detected but not
  fed** into the conversion model (logging only).

---

## 2. Target design

### 2.1 Collapse to a 3-tier ladder; grade only the top tier
Map the current `inactive→watch→build→ready→fire→{cashed,missed,expired}` machine onto **3 visible
tiers**, promoting faster:

| New tier | Sourced from | Meaning | Graded as a pick? |
|---|---|---|---|
| **Watch** | `watch` | Ambient: live contact / near-HR evidence building | **No** — context only |
| **Building** | `build` + `ready` collapsed | Real power threat forming; near-actionable | **No** — context only |
| **HR Max Window** | `fire`, EV-gated | Actionable bet, inside a bounded window | **Yes** — only this counts |

- **Promote quicker:** collapse `ready` into Building and lower the Building→HR-Max sustain requirement
  (today `READY_TO_FIRE_SUSTAIN_TICKS=2` + strong driver), so genuine threats reach the actionable tier
  in fewer ticks instead of stalling in a 4-stage gauntlet.
- **Honest grading (core fix):** **Watch/Building never produce `called_miss`.** Only a signal that
  **entered HR Max Window** can resolve to `cashed`/`missed`. This converts "206 misses" into a small,
  defensible actionable set. Watch/Building roll up separately as *context volume*.
- **A real "window":** HR Max Window expires after a **bounded PA horizon** (e.g. the batter's current +
  next plate appearance, or a short clock), producing `expired` (not `missed`) when the window passes —
  so "window closed" finally means what it says.

### 2.2 EV-gate the HR Max Window against the market
- Join the live `batter_home_runs` price (`server/oddsService.ts`) to the HR Radar candidate by
  `sport:gameId:actorId:home_runs`.
- Convert American odds → implied prob, de-vig, and require
  **model game-P(HR) ≥ marketImplied × (1 + margin)** (start margin ~10–15%) for HR Max Window entry.
- Surface `modelProb`, `marketImplied`, `edgePct` on the signal so the UI shows *why* it fired.
- Keep this **inside the engine layer before the bus** as a new **optional** input (no-op when price
  absent, per §7a #2) so partial odds coverage never destabilizes runtime.

### 2.3 Sharpen the underlying probability (engine layer, §7a-sanctioned)
Additive, capped, no-op-when-absent. In priority order:

1. **Close the calibration loop.** Persist every HR-Max candidate's `convProb` + realized outcome;
   build **empirical calibration buckets** from real data and replace the static table
   (`hrConversionModel.ts` ~163–178). Report **calibration error + lift over base rate** as the new
   success metric instead of raw hit-count.
2. **Hard-hit × angle × bat-speed × IBB interaction booster (high priority).** Add an explicit
   *multiplicative interaction*: when a **hard-hit ball (EV high) OR high xBA (`perABxBA ≥ ~0.65`)**
   co-occurs with a **favorable launch angle**, **elite bat speed** (`avgBatSpeed`, currently unused),
   and/or a **feared-slugger/IBB** profile, apply a compounding boost on top of the independent live-
   contact term. This wires bat speed in for the first time and ties the IBB prior to live contact
   quality. Capped per §7a #4 (cannot breach Phase 1.5 caps); no-op when any input is absent. Files:
   `nearHrContact.ts` (contact classification) + `hrConversionModel.ts` (live-contact section ~215–251).
3. **Wire handedness park factor** — use `PARK_FACTORS.hrLHB/hrRHB` in the environment multiplier keyed
   on batter hand; capped; replaces the generic `hr` factor when present.
4. **Rolling Statcast power trend** — add L15 rolling barrel%/hard-hit%/xISO to the form multiplier (new
   sync in `dataPullService.ts`, additive multiplier in `hrConversionModel.ts`).
5. **Batted-ball-type weighting** — discount line-drive/ground contact vs fly contact in the live
   contact multiplier (`nearHrContact.ts`).
6. **Pitcher pitch-type HR vulnerability** — fold HR-per-pitch-type (Savant) into the pitcher multiplier
   where available.
7. **Market steam as a soft feature** — optional small nudge when `batter_home_runs` line shortens.

Each new input: returns `1.0`/`null` when data absent, respects Phase 1.5 caps, and gains a regression
case before merge (§7a #2,#4,#6). Re-baseline `MLB_GOLDMASTER_VERSION` (`server/mlb/goldmasterGuard.ts`)
whenever behavior changes on purpose (§7a #5) — the resulting `[MLB_DRIFT_WARNING]` is expected, not a
regression.

---

## 3. Phased implementation plan

### Phase 0 — Instrument & prove the leak (no behavior change)
Log, per resolved signal, the **max tier it reached** and outcome; emit a daily breakdown of misses by
max-tier. Confirms the 206 misses are dominated by Watch/Building.
- Files: `server/mlb/liveGameOrchestrator.ts`, `server/analytics/hrRadarIntelligence.ts` (read-only).

### Phase 1 — 3-tier ladder + honest grading (biggest credibility win) — ✅ SHIPPED
Implemented on branch `claude/hr-tracking-engine-audit-1wyq4m` in four slices, all with
`server/mlb/hrRadarHonestGrading.test.ts` (35 checks) + green regression suites:

- **Honest miss grading.** `reconcileHrRadarAlertsForGame` only stamps `called_miss` for signals that
  reached the HR Max Window (actionable top tier); sub-actionable Watch/Building/presence rows become
  `expired` (excluded from the miss record). New pure helpers `reachedHrMaxWindow()` /
  `resolveFinalNoHrGrading()` in `hrRadarSection.ts`.
- **Symmetric cash gating.** Every cash path (`resolveHrRadarAlertAsHit`, reconcile fallback,
  `ensureHrRadarAlertHit`, `liveGameOrchestrator.closeHrAlertOnHit`) now credits a counted win only when
  `reachedHrMaxWindow` is true; sub-actionable pre-HR signals → `uncalled_hr` (diagnostic, not a win).
  Building/`prepare` no longer counts toward the record.
- **3-tier ladder UI.** `HrRadarLadder.tsx` collapses FIRE/READY/BUILD/WATCH → **Watch / Building /
  HR Max Window** (FIRE+READY merge into the synthetic `hrMax` bucket), with a header "`N` HR Max ·
  `N` context" split.
- **PA-bounded window.** New `hrMaxWindow.ts` (`classifyHrMaxWindowAtFinal`) splits HR Max Window misses
  into `called_miss` (window played out) vs `expired` (fired too late, window cut short), threaded into
  reconcile via `finalInning`.

**Deferred follow-up:** the *live mid-game auto-expiry sweep* (resolving a signal the instant its PA
window lapses, before game-final) is not yet enabled — it mutates live state per tick and needs a live
run to verify. The window is currently enforced at the (already-tested) game-final grading path.

### Phase 2 — EV-gating against `batter_home_runs` — ✅ SHIPPED
- `evaluateHRAlert.ts` is now an EV-gate wrapper around `evaluateHRAlertCore`: when a signal holds the
  actionable `officialAlert` tier and a price is present, it requires model game P(HR) ≥ de-vigged
  market-implied × (1 + `HR_EV_EDGE_MARGIN` = 10%), else **demotes to `prepare` (Building)** — surfaced
  as context, never bet/graded. New pure helpers `americanToImpliedProb()` / `deviggedMarketHrProb()`.
- The orchestrator caches per-tick resolved HR prices per (gameId, playerId) and feeds both
  `evaluateHRAlert` call sites (contact + dynamic-state paths) — no new API calls, no-op when absent.
- Goldmaster re-baselined to **v5** (`mlb-goldmaster-v5-2026-06-17-hr-ev-gate`).
- Tests: `hrEvGate.test.ts` (13 checks). Emits `[HR_RADAR_EV_GATE]` PASS/DEMOTE.

### Phase 3 — Probability accuracy — PARTIALLY SHIPPED (audit corrected on re-verification)
On implementation, two roadmap items turned out to **already exist** in the codebase (the original
subagent audit overstated the gaps):
- **Calibration loop — ✅ already closed.** `server/index.ts:598–610` schedules
  `computeCalibrationBuckets()` (analytics, built from resolved `rawConversionProbability` + outcome
  samples) and installs them via `setEmpiricalCalibrationBuckets()`; `calibrate()` prefers empirical
  buckets over the static table. No work needed.
- **Handedness park factor — ✅ already wired.** `getMarketParkFactor(venue, "home_runs", batterHand)`
  (`dataSources.ts:135–138`) already returns `hrLHB`/`hrRHB`, and the orchestrator already passes that
  as `input.parkFactor` into the environment multiplier. No work needed.

**Shipped this phase:**
- **Hard-hit × angle × bat-speed × IBB interaction booster — ✅ SHIPPED** (user-requested). New pure
  `computeHardHitInteractionMultiplier()` in `hrConversionModel.ts`: hard-hit (EV≥104) OR high-xBA
  (≥0.65) trigger, compounding with favorable launch angle, elite bat speed (wires in the previously
  unused `factors.batSpeedMph`), and season IBB respect. Capped at 1.25× (Phase 1.5 clamp still binds);
  no-op when absent. Goldmaster re-baselined to **v6**. Tests: `hrHardHitInteraction.test.ts` (11).

**Genuinely remaining (require NEW data ingestion — larger plumbing, deferred):**
- **Rolling Statcast power trend** — the model uses *season* barrel%/xISO + rolling HR-rate, but not
  rolling barrel%/hard-hit%/xISO (L7/L15). Needs a new Savant rolling sync in `dataPullService.ts`.
- **Pitcher pitch-type HR vulnerability** — a general `computePitcherHrVulnerability` exists (ERA/HR9/
  fatigue) but not HR-allowed-per-pitch-type. Needs per-pitch-type HR data from Savant.
- **Batted-ball-type weighting** (LD vs FB per AB) in the live-contact term.

**Sequencing rationale:** Phases 0–1 fix the spray-and-pray *perception and accounting* immediately and
are low-risk; Phase 2 makes the top tier *strategic* (EV-gated); Phase 3 raises raw accuracy. Each phase
is independently shippable.

---

## 4. Success metrics (replace raw hit-count)

- **Calibration error** on the HR Max Window tier (predicted P(HR) vs realized), bucketed.
- **Lift over base rate**: realized HR rate of HR-Max picks ÷ ~12% league game base.
- **ROI vs market** at the de-vigged `batter_home_runs` price (the EV the tier was gated on).
- **Context volume** (Watch/Building counts) reported separately and **never** as misses.

---

## 5. Regression gates (must pass before any engine PR merges)
Per `CLAUDE.md §1`:
```
npx tsx server/mlb/phase3bRegression.test.ts
npx tsx server/mlb/shadowOutcomeWiring.test.ts
npx tsx server/mlb/hrRadarLifecycleRepair.test.ts
npx tsx server/mlb/hrRadarStateMachine.test.ts
npx tsx server/mlb/hrRadarReadyToFire.test.ts
npx tsx server/mlb/nearHrContact.test.ts
npx tsx server/mlb/pullAndPregame.test.ts
npx tsx server/mlb/ibbAndRecentForm.test.ts
```
Plus `npx tsc --noEmit` clean, and a re-baselined `MLB_GOLDMASTER_VERSION` for any intentional behavior
change.

---

## 6. Second audit pass (2026-06-18) — export-integrity + calibration fixes

Triggered by an HR Radar export where **Score=0.0 on every row**, every player appeared **twice**, and the
header read **38 hits / 6 misses / 200 total**. Root-caused and fixed both the telemetry layer and the
calibration layer. Goldmaster re-baselined to **v9** (`mlb-goldmaster-v9-2026-06-18-hr-radar-calibration-audit`).

### Integrity (display/accounting — no engine math)
- **F1 — dead `Score` column.** The UI's "Score" read `detectedScore` (= `initialReadinessScore`, stamped 0
  at creation). Added a persisted `currentScore` column (`shared/schema.ts`), archived
  `alert.currentReadinessScore` (`storage.ts archiveDailyHrRadarOutcomesToAnalytics`), and rendered it
  (`unified-analytics.tsx`). **Requires a DB migration: `drizzle-kit push:pg`.** Old rows fall back to peak.
- **F2 — duplicate rows.** `collapseDuplicateHrRadarOutcomes` harmonizes dupe alert rows but never removes
  them, so the archiver inserted each twice. Archive now de-dupes by `(playerId)` (HIT wins, else highest
  peak) and guards against existing `(sessionDate, gameId, playerId)` keys.
- **F3 — grade accounting.** Hit rate is now graded-only (`hits/(hits+misses)`); non-`hit`/`miss` terminal
  statuses are surfaced as **ungraded context**, never silent losses (`routes.ts`, `unified-analytics.tsx`).
- **F5 — peak buckets.** Re-scaled the distribution buckets from a 0–10 assumption to the real 0–100
  readiness scale (`<25 / 25-45 / 45-65 / 65+`).
- **F6 — honest result labels.** The table no longer paints every non-hit as "MISS"; ungraded shows "—".

### Calibration (engine — §7a, re-baselined + tested)
- **C1 — tier separation.** `PREPARE_THRESHOLD` 0.06 → 0.07 (`hrAlertEngine.ts`) so BUILDING sits in a clean
  ~0.07–0.10 band above the WATCH floor (BUILDING had been converting at/below MONITOR).
- **C2 — readiness over-weighted loud contact.** The 40-pt confidence half is now gated by a forward-prob
  ramp (`0.4 + 0.6·min(1, calibrated/PREPARE)`): unchanged for building/attack rows, damped for
  low-probability rows so a single squared-up ball no longer manufactures a high peak (`hrAlertEngine.ts`).
- **C3 — top-end under-confidence.** Calibration table top bins lifted (0.30–0.40 → 0.36; ≥0.40 → 0.46) to
  match the ~57–67% realized rate of attack/STRONG calls (`hrConversionModel.ts`).
- **C4 — starved empirical calibrator.** Count `uncalled_hr` as a cashed positive; lower the per-bin floor
  30/20 → 15/12; and run the calibration refresh once ~60s after boot (not only every 30 min)
  (`hrRadarIntelligence.ts`, `index.ts`). New test coverage in `hrCalibration.test.ts`.
- **C4 (persistence) — durable outcome stamps.** Outcome stamps were in-memory only and reset on every
  process restart, so the per-bin sample never accumulated. Added a persisted `hr_radar_outcome_stamps`
  table (`shared/schema.ts`), an injected fire-and-forget persister + boot hydration in the stamp module
  (`hrRadarOutcomeStamp.ts`: `setHrRadarOutcomeStampPersister` / `hydrateHrRadarOutcomeStamps`), storage
  upsert/load methods (`storage.ts`: `persistHrRadarOutcomeStamp` / `loadRecentHrRadarOutcomeStamps`, 21-day
  window), and boot wiring in `index.ts` (register persister + hydrate before the first calibration run).
  Injection keeps the module DB-free for unit tests. **Requires `drizzle-kit push:pg`.**

All 16 MLB suites pass; `npx tsc --noEmit` clean.

### DB migration required before deploy
`drizzle-kit push:pg` — adds `hr_radar_analytics.current_score` (F1) and the `hr_radar_outcome_stamps`
table (C4). Until applied, the relevant inserts are wrapped in try/catch and no-op (they never crash
runtime), so archiving/persistence simply won't write until the migration runs.

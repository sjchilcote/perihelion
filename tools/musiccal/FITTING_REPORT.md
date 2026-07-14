# STALWART / CONTEMPT / PRAYER calibration — fitting report

Lane: `tools/musiccal/`. Produces the empirical factor curves that replace
`game/perihelion/music.py`'s hand-tuned battery (integration is the main
line's job; this lane only ships the fitted data + evidence).

**Everything here is measured on the real game binary's `GameSession`,
driven headlessly by HumanBot (the player model), no mocks.** The corpus is
regenerable bit-identically: runs are deterministic given (level SHA,
seed), and every run file's header records both.

## The design being calibrated (director, verbatim)

> "take a subset of mid-game segments and assemble them together, with rest
> and recharge lootrooms in the middle of long, safe corridors dividing
> them. Run a massive quantity of bots through this level - first, keep
> adjusting it so the total clear rate is maybe 50%. After enough runs -
> keep rerunning until the statistics reach saturation - the probability of
> bot death at any moment is our STALWART factor. The number of enemies
> killed per second is our CONTEMPT factor, and the inverse of number of
> enemies currently aggroed is our PRAYER factor."

Methodology correction (director, 2026-07-13, superseding pre-binned
hazard curves): capture **all** raw per-tick data, compute the
ensemble-level north-star labels afterward, and run factor analysis to
*discover* which observables predict P(death at this moment), keeping the
originally-guessed feature as an explicit baseline comparison.

## Pipeline (files)

| step | file | output |
|---|---|---|
| gauntlet assembly | `tools/musiccal/build_gauntlet.py` | `levels/gauntlet_cal.json` + `tools/musiccal/gauntlet_meta.json` (room-zone map) |
| clear-rate tuning | `tools/musiccal/tune_density.py` | `tools/musiccal/tuning_log.json` |
| run farm (raw capture) | `tools/musiccal/run_farm.py` | `tools/musiccal/runs/*.jsonl.gz` (gitignored, regenerable; 1 header + 1 array/tick + 1 footer) |
| analysis / fitting | `tools/musiccal/fit_factors.py` | `tools/musiccal/factor_model.json` + `hazard_by_position.png` |
| extended saturation (streaming, O(rooms) memory) | `tools/musiccal/saturation_stream.py` | `tools/musiccal/saturation_extended.json` |
| structural tests | `game/tests/test_gauntlet_level.py` | — |
| output schema + sanity pins | `game/tests/test_gauntlet_calibration.py` | — |
| CONTEMPT aux levels | `tools/musiccal/aux/build_heavy_probe.py` (+ full-density build via `build_gauntlet.py --density 1.0`) | `tools/musiccal/aux/*.json` |

## The gauntlet

Six combat clusters copied (geometry + spawns, never referenced) from the
shipped mid-game levels, ordered easy→hard, joined by seven long
stub–loot–stub corridors (each loot room: 2 medkits + one stack of each
ammo type). No keys, no gates — combat only. Bot loadout is a fixed
"just past l03" state (`run_farm.MID_GAME_STATE`: smg+shotgun, 60×9mm,
16 shells), because the segments are mid-game content.

| tag | source | rooms | roster at density 1.0 |
|---|---|---|---|
| B | l06 | 18,19,20 | husk, mite, spitter (3) |
| A | l04 | 4,55,56 | husk×4, mite×2, spitter (7) |
| C | l07 | 2,214 | spitter×2, husk×2 (4) |
| D | l07 | 13,16,17,18,20,21,22 | husk×4, flicker×2, mite (7) |
| E | l05 | 1–7 | husk×8, mite×3, spitter×3, brute (15) |
| F | l06 | 170,171,172 | husk×4, spitter, brute, shrieker (7) |

## Clear-rate tuning: 49.6% (target 45–55%), 11 iterations across 3 phases

Full trace in `tuning_log.json`. Summary:

- **Phase 1** — bisection on the `--density` knob (enemy COUNT scale,
  never stats), n=60 probes: 6 iterations (0.54→0.31→0.195→0.2525→0.2238
  →0.2381, clear rates 0.00/0.22/0.57/0.32/0.65/0.53), landed in-band at
  n=60 but the n=150 confirm read 0.42 — n=60 probes are too noisy in
  this steep region.
- **Phase 2** — fine sweep, n=120 each at densities 0.225/0.230/0.235/
  0.240. All four round to the **same 10-enemy level**, so this is 4
  independent samples of one level: 0.475/0.583/0.483/0.525, pooled
  **0.517 ± 0.023** (n=480).
- **Phase 3** — locked density = 10/43 exactly; fresh n=250 confirm:
  **0.496**.

The final calibration corpus itself (1200 runs, disjoint seed range
0–1199) landed at **0.490** — four independent estimates of the same
level all inside the band.

**Tuning-mechanism failure worth recording:** density v1 scaled each
room's count independently via `round(count × density)`. With ~20 rooms
holding 1–4 enemies each, most rooms' rounding cusps coincide at
density=0.25, so a 0.7% density change (0.2489→0.2507) jumped the level
from 5 enemies to 15 and clear rate from ~100% to 10%. Replaced with a
proportional-fair global order (`build_gauntlet._fair_order`: sort key
`(room_pos+0.5)/room_size`, any prefix is a fair cross-room sample) before
any committed numbers were collected. v1's measured cliff is preserved in
`tuning_log.json`'s caveats.

## Corpus and saturation

**Main corpus: 2400 runs** (seeds 0–2399, four batches; 16,434,240
valid-labeled ticks = 76.1 bot-hours). Outcomes: 1214 died / 1186
complete → **clear rate 0.494**. Per-batch clear rates 0.530 / 0.500 /
0.465 / 0.498 (batch summaries: `runs_summary_batch*.json`). Wall clock
≈ 4.5 min of farm total at 24–32 workers (~9 runs/s) — generating data
is not the binding constraint; the criterion is (below). **The fitted
model (`factor_model.json`) uses the first 1200 runs** (its header
records this); the second 1200 were added as a further saturation
doubling, evaluated by the memory-bounded streaming pass
(`saturation_stream.py` → `saturation_extended.json`) because holding
2400 runs' full feature arrays exceeds this box's contended RAM. Model
stability across 300/600/1200 (below) shows refitting on 2400 would not
move the shipped curves.

Auxiliary corpora (CONTEMPT sanity only, never in the fit): 80 runs at
density 1.0 (all six segments, clear rate 0.0) + 150 runs on the
heavy-segments-only probe (E+F at full density; clear rate 0.007).

### Convergence table

Seed-ordered prefix re-estimates (seeds are i.i.d., so prefixes are
valid batch reruns; the 300-prefix is exactly batch 1, etc.).
Tick-weighted 3s-hazard by zone:

| runs | valid ticks | combat | corridor | loot |
|---|---|---|---|---|
| 75 | 531,573 | 0.01029 | 0.00590 | 0.01584 |
| 150 | 1,063,528 | 0.01070 | 0.00643 | 0.02017 |
| 300 | 2,096,646 | 0.01243 | 0.00678 | 0.02256 |
| 600 | 4,194,499 | 0.01261 | 0.00676 | 0.02383 |
| 1200 | 8,222,519 | 0.01226 | 0.00735 | 0.02694 |
| 2400 | 16,434,240 | 0.01208 | 0.00719 | 0.02708 |

Zone-level hazard is stable to ±2% over the last doubling, and the
ordering **loot > combat > corridor** holds at every single prefix from
75 runs on (see contradiction #1).

Representative per-room trajectories (hazard; `~d` = estimated deaths in
that room at 2400 = positive ticks/180):

| room (zone/seg) | 75r | 150r | 300r | 600r | 1200r | 2400r | ~d@2400 |
|---|---|---|---|---|---|---|---|
| 14 (combat/D) | .0237 | .0503 | .0577 | .0616 | .0595 | .0521 | 58 |
| 10 (combat/D) | .0226 | .0378 | .0425 | .0471 | .0482 | .0461 | 46 |
| 38 (loot) | .0450 | .0494 | .0506 | .0505 | .0501 | .0542 | 233 |
| 35 (loot) | .0509 | .0434 | .0372 | .0362 | .0389 | .0378 | 175 |
| 36 (corridor) | .0094 | .0124 | .0166 | .0165 | .0186 | .0189 | 113 |
| 33 (corridor) | .0243 | .0161 | .0190 | .0151 | .0126 | .0114 | 78 |
| 6 (combat/C) | .0109 | .0111 | .0199 | .0199 | .0126 | .0154 | 24 |

Literal-criterion evaluation per doubling (`saturation_extended.json`):

| doubling | covered rooms | SE<15% ok | shift<15% ok | bins shifted >15% | median obs/pred shift |
|---|---|---|---|---|---|
| 75→150 | 40 | no | no | 17 | 0.36 |
| 150→300 | 39 | yes | no | 13 | 0.29 |
| 300→600 | 39 | yes | no | 14 | 0.36 |
| 600→1200 | 39 | no | no | 16 | 0.34 |
| 1200→2400 | 40 | no | no | 14 | 0.38 |

### Saturation verdict — honest three-layer answer

The brief's criterion: *SE < 15% of estimate for bins covering ≥95% of
bot-time AND the last doubling shifts no such bin by >15%.* **Not met at
2400 runs, and the trajectory shows why it can't be met at any feasible
n as literally specified:**

1. **Tick-level SEs are a false instrument here.** One death paints up to
   180 consecutive ticks positive, so ticks within a run are heavily
   autocorrelated and the binomial tick-SE overstates precision by
   ~√180 ≈ 13×. The honest sample-size unit is **deaths-per-room**
   (validated: summing positive-ticks/180 over rooms gives ~1221 vs 1214
   actual deaths). Per-room death counts at 2400 runs range from ~230
   (busiest loot room) down to **0–10 for a third of the 95%-coverage
   set**.
2. **The observed batch-to-batch shifts are exactly death-count sampling
   noise.** The streaming evaluator compares each bin's observed relative
   shift against the Poisson prediction √(1/d_cur + 1/d_prev): the median
   observed/predicted ratio is **0.29–0.38 at every doubling** (constant
   ratio, shrinking absolute shifts — the signature of an unbiased
   estimator converging at the honest rate; the <1 value reflects prefix
   nesting). Nothing is drifting; the bins that fail the 15% test are
   simply the ones with <45 deaths, and which bins those are rotates
   between doublings.
3. **Projection:** relative shift <15% needs ≳45 deaths per bin. The
   low-traffic third of the coverage set accrues deaths at ~1–5 per 1200
   runs, so the literal criterion projects to **~10,000–50,000 runs** —
   generatable in under two hours at this farm's throughput, but it would
   be precision spent on the *per-position sanity visualization*, which
   the brief itself demotes in favor of feature-binned curves ("bin over
   FEATURES ... so curves generalize").

**What is saturated — the shipped artifact:** the feature-binned fitted
model is stable across corpus doublings: held-out AUC 0.992 / 0.984 /
0.989 at 300 / 600 / 1200 runs (baseline 0.795 / 0.774 / 0.802), the
same features selected with the same signs, top-decile calibration
0.1359 predicted vs 0.1362 observed at 1200, zone-level hazards ±2% over
the last doubling, and clear rate 0.494 ± 0.010 across four independent
batches. Total corpus: **2400 main + 230 auxiliary = 2630 runs.**

## Factor discovery

### PCA (structure of the raw observables; 34 features, standardized)

| component | EVR | top loadings | reading |
|---|---|---|---|
| PC1 | 19.6% | weighted_threat +0.37, n_aggro_same_room +0.35, min_enemy_dist −0.35, has_same_room_threat +0.35, n_aggro +0.32, hp −0.26 | **threat proximity** (the fight, as pressure) |
| PC2 | 14.7% | hits_3s +0.43, kills_3s +0.43, accuracy_3s +0.40, shots_3s +0.33 | **violence output** (the fight, as throughput) |
| PC3 | 10.3% | is_loot_zone +0.50, n_pickups_room +0.49, area +0.48, n_lights +0.31 | **rest-room context** |
| PC4 | 8.4% | weapon smg +0.49 vs shotgun −0.49 | loadout identity |
| PC5 | 7.7% | total_ammo +0.55, ammo_9mm +0.54 | reserves |

Threat-pressure and kill-throughput are *separate axes* (PC1 ⊥ PC2) — the
data itself says STALWART-ish and CONTEMPT-ish are independent factors,
which corroborates the director's engine ruling that they are separate
continuous values rather than points on one intensity dial.

### STALWART — fitted hazard model

L1 logistic regression, label = death within 3s (180 ticks), fitted on
150,082 ticks / evaluated on 49,918 ticks from **held-out runs** (25%
GroupShuffleSplit by run id; C chosen by 3-fold group-aware CV on the
train split only; timeout-run tails censored).

| model | out-of-sample AUC |
|---|---|
| **wide feature set (30 nonzero coefs)** | **0.9888** |
| baseline: `weighted_threat_active` alone (the pre-correction guess) | 0.8015 |
| wide, 5s horizon | 0.9768 |
| wide, 10s horizon | 0.9482 |

The factor analysis beats the pre-selected single feature by **+0.19 AUC
out-of-sample** — the director's correction was right that the data knew
better than the guess. Held-out calibration is excellent where it
matters: top predicted-risk decile 0.1359 predicted vs 0.1362 observed;
bottom nine deciles predict ≈0 and observe ≈0.

Top standardized coefficients (sign = direction of death risk):

| feature | coef | reading |
|---|---|---|
| hp | −4.56 | the dominant factor by ~2.5× |
| min_enemy_dist_capped | −1.85 | closer live enemy → higher hazard |
| has_same_room_threat | −1.84 | joint with min_dist: the "500 = empty room" placeholder correction |
| weighted_threat_active | +1.03 | the original guess — real, just not sufficient |
| **is_loot_zone** | **+0.66** | **death risk is HIGHER in loot rooms, all else equal** (see contradictions) |
| area | −0.64 | big rooms are survivable; corridors kill |
| speed | −0.62 | still moving → alive; pinned → dying |
| shots_3s | −0.40 | still shooting → still fighting back |
| dmgtaken_3s | +0.20 | recent damage → more coming |

Shape in words: raw P(death|3s) is a **spike, not a slope** — p50 of the
fitted probability is 2×10⁻⁶, p90 = 0.006, p95 = 0.034, p99 = 0.45. The
Commando is almost always fine; STALWART lives in the top few percentiles
where low hp meets a same-room enemy inside ~100 units. The percentile
normalization (101-point ensemble CDF in `factor_model.json:
stalwart.cdf_reference`) is therefore essential — it converts the spike
into a usable 0–1 ride. There is no "knee at weighted threat ≈ 7":
weighted threat alone never gets past AUC 0.80 because **hp is the
knee** — the same threat reads harmless at 100 hp and lethal at 25.

### CONTEMPT — kills/sec (directly observed, per the brief)

Binned by same-room weak (husk/mite) aggro count, main corpus:

| weak aggro in room | bot-ticks | kills/sec | SE |
|---|---|---|---|
| 0 | 6,411,839 | 0.0635 | 0.00006 |
| 1 | 1,377,098 | 0.0652 | 0.00013 |
| 2 | 352,039 | 0.0455 | 0.00023 |
| 3 | 62,603 | 0.0421 | 0.00052 |
| 4+ | 18,940 | 0.0220 | 0.00070 |

Shape in words: **flat then declining** — kill throughput peaks at 0–1
weak enemies engaged and *falls monotonically as the swarm grows* (the
bot's throughput saturates and it kites). Kills/sec is therefore lowest
exactly where the emotional spec says contempt should read highest
(mowing a swarm). The engaged-tick distribution is also extremely spiky
(75% of engaged ticks have 0 kills in the trailing 3s; p90 = 1 kill/3s).
The percentile CDF is in `factor_model.json: contempt.cdf_reference`.

### PRAYER — 1/(1+n_aggro) (directly observed, per the brief)

| zone | mean PRAYER (global formula) | room-local diagnostic |
|---|---|---|
| loot | 0.640 | 0.746 |
| corridor | 0.689 | 0.779 |
| combat | 0.668 | 0.826 |

Shape in words: **flat across zones** (spread ~0.05) — the formula as
specified does not discriminate rest from combat in this engine (see
contradiction #3). Validation target "~1.0 in rest rooms" **fails**:
0.640 vs 1.0.

## Sanity checks (fail-first) — what actually held

All three direction-checks are computed once on the real corpora in
`fit_factors.py` and pinned by `game/tests/test_gauntlet_calibration.py`.
The permutation machinery is sound — the shuffled-label control reads
≈0 (−6×10⁻⁶ ± 5×10⁻⁴) while the real split is significant (p=0.012) — so
these are measurements, not artifacts. **But two of the three
hypothesized directions are false, and the third failed its target:**

## Contradictions of the design assumptions (read back to the director)

1. **The "rest and recharge lootrooms" are the deadliest zone class in
   the gauntlet — 2.2× the combat rooms.** Three-way decomposition
   (3s-hazard, 16.4M ticks, stable at every prefix from 75 runs on):
   **loot 0.0271, combat 0.0121, corridor 0.0072.** The pooled sanity
   statistic (corridor+loot 0.0139 vs combat 0.0126, permutation p=0.012
   vs shuffled-label control ≈0) is pinned in
   `test_gauntlet_calibration.py`; the decomposition shows it is driven
   entirely by the loot rooms — the corridors themselves are the SAFEST
   zone, so "long, safe corridors" actually held. Two mechanisms, both
   visible in the fitted model:
   - **Pursuit never ends.** Read directly from
     `game/perihelion/sim.py::_enemy_ai`: standard enemies have no
     de-aggro transition — once `state=="hunt"` they pathfind to the
     player's *current* room via `next_edge(room, proom)` forever (only
     the flicker disengages). Fight survivors follow the player through
     the corridor and into the loot room.
   - **Loot rooms concentrate the nearly-dead.** Hurt bots deliberately
     path to medkits (HumanBot's medkit-seeking, mirroring real player
     behavior), so the population standing in loot rooms is
     hp-selected — and hp is the model's dominant hazard factor (−4.56).
     The +0.66 is_loot_zone coefficient shows extra risk *beyond* the
     hp effect: cornered in a 220×220 box with pursuers arriving.
   The per-position plot (`hazard_by_position.png`) shows the green
   (loot) points riding at or above the neighboring red (combat) points
   through the whole mid-gauntlet. **Design implication for the
   director's premise: a loot room between segments is not a rest beat —
   under permanent pursuit it is where wounded runs go to end.**

2. **CONTEMPT (kills/sec) is NOT higher against trash than against
   heavies.** Kind-specific same-room-aggro conditioning, full-density
   corpora: trash-engaged 0.295 kills/s vs heavy-engaged 0.477 kills/s.
   Checked twice (segment-level and per-kind conditioning; dedicated
   heavy probe with 36,314 heavy-engaged ticks). Plausible mechanism,
   flagged as hypothesis: E/F's heavies arrive with escorts, and escort
   kills land during heavy engagement, inflating the heavy-conditioned
   rate; a "solo heavy" tick population wasn't isolated. Combined with
   the declining-by-swarm-size table above: **raw kills/sec is a poor
   CONTEMPT proxy — it tracks target availability and TTK, not the
   mowing-trash feeling.** A better proxy from this same data: weak-kind
   kill *share* per window, or kills/sec *normalized by weak-aggro
   count* — the main line can derive either from `factor_model.json`'s
   raw stats without new runs.

3. **PRAYER does NOT read ~1.0 in loot rooms** (0.640 measured, target
   ~1.0). Same root cause as #1: the global aggro count rarely returns to
   zero once anything upstream survived. The room-local diagnostic
   variant (1/(1+n_aggro_same_room)) reads 0.746 — higher, confirming
   distant immortal hunters are a large part of the depression — but not
   ~1.0 either: at the tuned density, pursuers physically catch up and
   enter the loot room with the player. **PRAYER as "inverse of enemies
   currently aggroed" is measuring the pursuit system, not calm.** Note
   for the main line: `music.py::read_inputs` counts aggro the same
   global way, so the live PRAYER heuristic inherits this — after the
   first surviving aggro, the music's calm channel can stay suppressed
   for the rest of a level.

4. **The 50% clear-rate target and "mid-game segments with their enemy
   rosters" are jointly unsatisfiable at this loadout.** The unscaled
   six-segment gauntlet (43 enemies) is 0% clearable by the player-model
   bot; 50% requires keeping only 10 of 43 spawns, and the fair-order
   prune leaves **zero brutes/shriekers/wardens** in the tuned level.
   The calibration corpus therefore contains no heavy-class combat, which
   is why CONTEMPT's trash-vs-heavy check needed auxiliary full-density
   corpora. Any future recalibration wanting heavies *in* the main corpus
   needs either a stronger loadout, per-segment clear gates, or per-run
   spawn rotation rather than one global density knob.

5. **The literal saturation criterion cannot be met** on near-zero-hazard
   bins (relative SE of a ≈0 estimate); see the saturation section for
   the amended absolute-floor evaluation that was met at 1200 runs.

## Turret intervention (2026-07-13 follow-up) — finding #1, remedied and measured

Director's directive, verbatim: *"let's put friendly turrets in the
safe-room corridors."* Built: a stationary, indestructible, LOS+range-
gated friendly emplacement (`SENTRIES`/`spawn_sentry`/`_sentry_tick` in
`game/perihelion/sim.py`; entity type `"sentry"`, pistol-class damage/rof,
260-unit range, walk-mask-terrain LOS via `_sentry_los_clear`, ~0.17s
target-acquisition spin-up; reuses the cloister guardians' `kind="turret"`
bullet tag so the existing player-immunity guard in `_contact` covers it
for free). Placed one per loot room (`tools/musiccal/build_gauntlet.py`'s
`add_corridor`), density knob untouched (still 10/43 enemies, `--density
0.232558`) so any measured delta is attributable to the turrets alone.
Fail-first unit/integration tests: `game/tests/test_sentry_turret.py`.

**Methodology correction, mid-measurement:** `tools/musiccal/run_farm.py`
on the freshly-turreted level (60 runs, seeds 0–59, same `MID_GAME_STATE`
loadout) read **clear rate 1.000** — every run complete, zero deaths. A
naive read against this report's 0.494 baseline would overstate the
turrets' effect enormously. Checked instead of reported: a MATCHED
control (the same 60 seeds, same HumanBot code, same density, built from
the pre-turret `build_gauntlet.py` at commit `2ecb7fe`) also cleared at
**0.967** (58/60) — nowhere near 0.494 either. Root cause (confirmed via
`git log` / `git diff` on `game/perihelion/testkit/{humanbot,perception}.py`
between the calibration commit and now): HumanBot's perception and
movement were substantially retuned by unrelated concurrent work in this
shared checkout after this report's corpus was captured (portal-visibility
widening, shorter/rarer hesitation rituals, gentler turn speed-shedding —
see commit `0489cda`). **The 0.494/2.2x numbers above are pre-retune and
are no longer this bot's baseline; they are not a valid zero-turret
control for this measurement.** The matched same-seed, same-bot,
turret-vs-no-turret comparison below is the valid one.

Matched comparison, extended to 600 runs (seeds 0–599, both levels built
at the identical `--density 0.232558`) for a death count large enough to
read:

| | clear rate | deaths (n=600) | combat hazard | corridor hazard | loot hazard | loot/combat |
|---|---|---|---|---|---|---|
| no-turret (matched control) | 0.9817 | 11 | 0.000310 (~2.2 deaths) | 0.000232 (~2.1 deaths) | **0.002415 (~6.8 deaths)** | **7.79x** |
| turreted | **0.9983** | **1** | 0.000143 (~1.0 deaths) | 0.000000 | **0.000000** | **0.00x** |

Turreted-level primary numbers (director's literally-requested 60-run
batch, seeds 0–59): clear rate 1.000 (60/60), hazard 0.0 in every zone.

**Verdict: the acceptance criterion is met, and by a wide margin.** With
the modern (retuned) bot, loot rooms are *still* the deadliest zone by
far when undefended — 7.79x combat, actually a worse ratio than this
report's original 2.24x, consistent with the mechanism in finding #1
(a bot that got much better at combat concentrates its remaining deaths
in the one place with no defense at all). With turrets, loot-room deaths
go to exactly **zero** at n=600 — safer than combat, not just safer than
before. The single surviving death (seed 328, 600-run turreted batch) was
verified in the raw run file to be an ordinary combat-room death (room 9,
`zone=="combat"`, hp draining to 0 in room) — outside the turrets' scope
by design (director's order: gauntlet loot-room corridors only, campaign
placement deferred). Turrets also have a small, plausible secondary
effect on combat hazard itself (0.000310 → 0.000143): a run that survives
a loot room at full health rather than half-dead-or-not-at-all enters its
next fight healthier, and `hp` is this report's dominant hazard
coefficient (−4.56) — noted as a hypothesis, not re-verified at this
sample size (only ~1 vs ~2 combat deaths).

## Output artifact

`tools/musiccal/factor_model.json` (schema 2, pinned by
`test_gauntlet_calibration.py`):

- `stalwart`: fitted L1 logistic (feature names, standardized
  coefficients, intercept, scaler mean/scale — everything needed to
  evaluate P(death|3s) live), held-out AUC + calibration curve, the
  baseline comparison, secondary-horizon AUCs, and the 101-point
  percentile `cdf_reference` for 0–1 normalization.
- `contempt`: kills/sec lookup by weak-aggro bin (+ SEs) and the engaged
  ensemble `cdf_reference`.
- `prayer`: per-zone means for the specified formula plus the room-local
  diagnostic.
- `pca`, `saturation` (criterion, batches, evaluation),
  `per_room_hazard_final_batch`, `room_hop_order`, `sanity_checks`, run
  metadata (n, outcomes, clear rate, git rev, level SHA).

## Caveats

- All curves are conditioned on HumanBot at skill 4.0 with the fixed
  MID_GAME_STATE loadout on this one gauntlet. Feature-binned (not
  position-binned) fitting is what lets them transfer, but transfer to
  real human play is unvalidated.
- The death label is sparse (1.34% of ticks at 3s horizon); the model's
  AUC is driven by the easy mass of safe ticks. The top-decile
  calibration match (0.136 vs 0.136) is the load-bearing validation.
- `hp` dominating the model partially reflects the label (dying soon ⇒ hp
  already falling). It is still the honest answer to "P(death at this
  moment)" — but a music integration that wants anticipation rather than
  confirmation should weight the proximity terms; the 10s-horizon model
  (AUC 0.948) is fitted and included for exactly that trade.
- CONTEMPT escort-inflation mechanism (#2) is a hypothesis; the direction
  of the measurement itself is replicated and solid.
- Density v1's rounding-cusp failure is documented in
  `tuning_log.json` — do not resurrect per-room rounding.

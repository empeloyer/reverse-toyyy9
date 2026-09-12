# BTCUSDT 5-Minute Candle Signal — Native Android App

A native Kotlin + Jetpack Compose Android application that predicts whether the
currently-forming BTCUSDT 5-minute candle will close GREEN or RED, using **only** the
31 strategies defined in `strategies_parameters.json` (9 carried over from the original
27-strategy research report, 22 added during the 2026-09 one-year re-evaluation — see
"§19 One-year re-evaluation (2026-09)" below for exactly what changed and why).
No strategy logic, threshold, or parameter has been invented, modified, or optimized
beyond what that re-evaluation documents — see "Strategy fidelity" below for exactly
how that's enforced architecturally.

---

## 1. Project overview

- **Signal engine**: reads the Strategy Database from `app/src/main/assets/strategies_parameters.json`
  at runtime and evaluates every strategy's exact components/thresholds generically — the
  JSON *is* the executable logic, not a reference a human transcribed into 31 separate
  classes. See "Strategy fidelity" below.
- **Live Engine**: Binance public WebSocket (`wss://stream.binance.com:9443/ws/btcusdt@kline_1m`)
  → `MarketDataStore` (closed-candle buffers) → `CandleAggregator` (5m construction,
  Checkpoint A/B, phase tracking) → `CoreSignalEngine` → Room persistence → Android
  notification.
- **Backtest Engine**: Binance public REST klines, replayed chronologically through the
  **exact same** `CoreSignalEngine`, `MarketDataStore`, and `CandleAggregator` as the
  Live Engine — not a second implementation.
- **UI**: Jetpack Compose, Material 3, dark trading-dashboard theme, 6 screens (Live,
  Strategies, Backtest, History, Performance, Settings).

## 2. Architecture

```
app/src/main/java/com/btcsignal/app/
├── data/
│   ├── model/          Candle, Signal, StrategyDef, MarketRegimeState, enums
│   ├── binance/         BinanceRestClient, BinanceWebSocketClient (public market data only)
│   ├── local/            Room: SignalEntity, SignalDao, AppDatabase
│   └── repository/     SignalRepository, SettingsRepository (DataStore)
├── engine/
│   ├── indicators/       Indicators.kt — RSI, Stochastic, CCI, Williams %R, MACD, ADX/DI,
│   │                    EMA, Bollinger %B, OBV, ATR, ROC, Marubozu, Momentum Ratio V2
│   ├── StrategyRegistry.kt      Parses strategies_parameters.json — SINGLE source of truth
│   ├── MarketDataStore.kt       Closed-candle buffers, 1m→5m/1h/4h aggregation
│   ├── MarketRegimeClassifier.kt Trend/Volatility/Momentum regime (report section 1.5)
│   ├── CandleAggregator.kt      5m construction + Checkpoint A/B timing
│   ├── ComponentEvaluator.kt    Evaluates ONE strategy component against live data
│   ├── DynamicScore.kt          Section 10 scoring formula
│   ├── ConflictResolver.kt      Section 8 conflict-resolution logic
│   └── CoreSignalEngine.kt      THE shared engine — used identically by Live and Backtest
├── live/                LiveMonitoringService (foreground service), LiveEngineState,
│                        BootRestartReceiver
├── backtest/             BacktestEngine (historical replay via the same CoreSignalEngine)
├── notifications/        NotificationHelper (real Android notifications, one channel)
└── ui/                   Compose screens, theme, reusable components
```

## 3. Strategy fidelity — how "do not invent or modify strategies" is enforced

Rather than hand-writing 27 near-duplicate strategy classes (which risks silent
transcription drift), the engine is **data-driven**: `StrategyRegistry` parses
`strategies_parameters.json` verbatim into `StrategyDef`/`StrategyComponent` objects that
preserve every field from the source file, and `ComponentEvaluator` executes each
component type (`RSI`, `CCI`, `MACD_cross`, `ADX_DI_direction`, etc.) using the exact
rule described in that indicator's section of `BTC_5m_Strategy_Research_Report.md`,
driven entirely by the JSON's own parameters (period, thresholds, timeframe, hypothesis).
Nothing about any individual strategy is hardcoded per-strategy anywhere in the app.

`StrategyRegistryTest.kt` includes an automated coverage check (spec sections 47-48):
it asserts every `STRAT-xxx` id present in the raw JSON text is present in the parsed
`StrategyDatabase`, and that every parsed strategy retains at least one component.

## 4. Documented ambiguities (per the master prompt's "do not guess" rule)

The Strategy Database is complete for entry logic, thresholds, and regime definitions,
but leaves a few implementation details unspecified. Per the master prompt's own
instruction ("if ambiguous, do not guess — document it"), here is exactly what was
filled in, how, and why it does not constitute inventing/modifying strategy logic:

1. **Indicator smoothing method.** RSI/ADX/ATR periods are given (e.g. "RSI(7)") but not
   the smoothing method. Implemented with the industry-standard Wilder smoothing,
   applied identically for every strategy and both engines — not tuned per strategy.
2. **Fixed thresholds not present as JSON fields**: Bollinger %B mean-reversion
   (< 0.05 / > 0.95) and Williams %R (< -80 / > -20) are described consistently in the
   report's prose for every strategy that uses them, but the JSON `components` blocks for
   those primitives only carry `period`/`std`/`timeframe` — not the threshold itself.
   These are hardcoded as primitive-level constants in `ComponentEvaluator`, exactly
   matching the report text, not chosen or tuned by this implementation.
3. **Marubozu body-to-range ratio.** The report names the pattern but not the exact
   ratio; 90% is the standard definition and is applied identically to bullish and
   bearish detection (not tuned to favor either).
4. **Signal-window granularity.** The master prompt (section 7) describes "continuous
   monitoring throughout Minute 2"; the Strategy Database itself (`meta.hard_constraints
   .checkpoints`) defines exactly two discrete evaluation points — Checkpoint A
   (immediately after minute 1 closes) and Checkpoint B (immediately after minute 2
   closes, only if A did not fire). Per the master prompt's own rule 0 ("the Strategy
   Database is the authoritative source... if explicitly defined, implement it exactly"),
   the app implements the two-checkpoint model precisely as the database defines it,
   rather than continuously re-evaluating on every sub-second price tick during Minute 2.
5. **Dynamic Score penalty terms.** Section 10's formula names
   `Penalty_if_regime_mismatch` and `Penalty_if_high_overlap_with_higher_score_strategy`
   without a coefficient or formula. `Penalty_if_regime_mismatch` is structurally always
   0 because mismatched strategies are excluded *before* scoring (never scored down).
   `Penalty_if_high_overlap...` is left at 0.0 rather than inventing a coefficient; the
   field it would need (`max_signal_overlap_with_other_selected_strategies_pct`) is
   already exposed on `StrategyDef` for a future revision once that coefficient is
   supplied.
6. **Conflict-resolver confidence threshold normalization.** The report proposes "a 3%
   normalized score gap" without defining the normalization basis. Implemented as
   `(top - second) / max(|top|, |second|, ε) >= 0.03`, the most direct literal reading.
7. **Dynamic Score recent-window fallback.** On a fresh install with no live signal
   history yet, `Expected_PnL_per_Signal_recent_window` and `N_signals_recent_window`
   fall back to the strategy's own Out-of-Sample numbers from the Strategy Database,
   since the formula's own inputs don't exist on day one.

None of the above changes any strategy's entry conditions, thresholds, direction logic,
or regime gate — they only resolve *how the surrounding engine* (indicator math,
timing granularity, scoring plumbing) is implemented where the source documents
describe the concept but not every numeric implementation detail.

## 5. What this build has NOT been verified to do

Being transparent about the limits of this delivery: this project was built and
statically reviewed (package/import consistency, brace/paren balance, a literal
cross-check of every parsed JSON field against the source) in an environment **without**
the Android SDK, Gradle, or network access to fetch Gradle/Maven dependencies. It has
**not** been compiled, and no Debug APK has been produced or installed on a device.
Opening it in Android Studio (which will download the Gradle wrapper, SDK components,
and dependencies automatically) is required to actually build and run it, and some
number of small fixes are realistically possible on first build — that's normal for a
project this size assembled without a build step in the loop. Please treat the first
`Sync Gradle` / `Build` in Android Studio as part of this deliverable's setup, not as a
sign something went wrong.

## 6. Requirements

- Android Studio Koala (2024.1) or newer
- Android SDK Platform 34, Build Tools matching AGP 8.5.2
- JDK 17 (bundled with recent Android Studio)
- A device or emulator running API 26+ (Android 8.0+)
- Internet access (Binance public REST + WebSocket; no API key needed)

## 7. Opening and building

1. Unzip `BTCUSDT_Signal_Android_Project.zip`.
2. Open the folder in Android Studio: **File → Open**, select the project root
   (the folder containing `settings.gradle.kts`).
3. Android Studio will prompt to install/generate the **Gradle wrapper jar**. This
   project ships `gradlew` / `gradlew.bat` and a `gradle/wrapper/gradle-wrapper.properties`
   that genuinely points at Gradle 8.7 (as of the §20 revision — it was previously 0
   bytes despite this file's own older claim otherwise, see Bug Report 3.1), but still
   not the binary `gradle-wrapper.jar` itself, since it couldn't be downloaded in the
   sandboxed environment either revision was assembled in (no network access there). If
   Android Studio doesn't prompt automatically, run **File → Sync Project with Gradle
   Files**, or from a terminal with any local Gradle install:
   `gradle wrapper --gradle-version 8.7` (this replaces the included `gradlew` /
   `gradlew.bat` — simplified stand-ins good enough to fail with a clear message rather
   than a cryptic one until then — with Gradle's own official versions, jar included).
4. **Sync Gradle** (automatic on open, or **File → Sync Project with Gradle Files**).
   This downloads AGP 8.5.2, Kotlin 1.9.24, Compose BOM 2024.06.00, Room 2.6.1, OkHttp
   4.12.0, and the other dependencies listed in `app/build.gradle.kts`.
5. **Build → Make Project** (or `./gradlew assembleDebug` from a terminal once the
   wrapper jar is present).

## 8. Running on an emulator

Tools → Device Manager → create a device with API 26+ → Run ▶ with the `app`
configuration selected.

## 9. Running on a physical phone

1. Enable Developer Options → USB debugging on the phone.
2. Connect via USB (or Wi-Fi debugging), authorize the computer when prompted.
3. Select the device in Android Studio's device dropdown and press Run ▶.

## 10. Enabling notification permissions

On first launch (Android 13+), the app requests `POST_NOTIFICATIONS`. If denied,
enable it manually: **Settings → Apps → BTCUSDT Signal → Notifications**. Sound/
vibration toggles and Test Notification/Test Sound buttons are on the **Settings**
screen.

## 11. Enabling background monitoring

The Live Engine runs as an Android **foreground service** (`LiveMonitoringService`)
with a persistent low-priority "Background Monitoring" notification, started
automatically when the app launches. On some OEM Android skins (Xiaomi, Huawei,
Samsung's aggressive battery optimization, etc.) you may additionally need to
disable battery optimization for the app: **Settings → Apps → BTCUSDT Signal →
Battery → Unrestricted**. `BootRestartReceiver` restarts monitoring after a device
reboot if it was running before shutdown.

## 12. Building a Debug APK

**Build → Build Bundle(s) / APK(s) → Build APK(s)**, or from a terminal:
```
./gradlew assembleDebug
```
Output location:
```
app/build/outputs/apk/debug/app-debug.apk
```
(standard Android Gradle Plugin output path for this project's module layout — this
project has one module, `app`, so no other path is expected).

## 13. Building a Release APK

```
./gradlew assembleRelease
```
Output: `app/build/outputs/apk/release/app-release-unsigned.apk`. Minification is
disabled by default (`isMinifyEnabled = false` in `app/build.gradle.kts`) to keep the
first build simple; enable and add signing config before shipping externally.

## 14. Installing the APK

Drag `app-debug.apk` onto an emulator, or:
```
adb install app/build/outputs/apk/debug/app-debug.apk
```

## 15. Known Android limitations

- Android's Doze mode / App Standby can still delay background work on some devices
  even with a foreground service, if the device is idle and stationary for long
  periods. This is a platform-level restriction, not a bug in this app.
- The WebSocket reconnect logic uses exponential backoff (1s → 30s cap); a fully
  offline device will show `DISCONNECTED`/`ERROR` in the Live screen until connectivity
  returns, at which point a gap-fill resync runs before any new signal can be generated
  (spec section 26).
- Notification channels are created per sound/vibration combination (Android does not
  allow changing an existing channel's sound/vibration after creation); toggling those
  settings switches which channel is used going forward.

## 16. Troubleshooting Binance connection issues

- Confirm the device/emulator has internet access and isn't behind a firewall blocking
  `api.binance.com` / `stream.binance.com:9443`.
- Some regions restrict access to Binance; a VPN may be required there — this app only
  uses Binance's public market-data endpoints (no account, no API key, no trading).
- Check the **Settings** screen's Status card for the current `AppState`
  (CONNECTING/CONNECTED/DISCONNECTED/SYNCING/ERROR).
- The Debug Trace (`engine/DebugTrace.kt`, accumulated in `LiveEngineState.debugTraceLog`)
  records every evaluated checkpoint, including why a signal was or wasn't produced —
  useful for diagnosing "no signals appearing" reports that are actually the engine
  correctly declining to signal (e.g. price outside the ±0.03% entry range, or
  conflicting strategies below the confidence threshold).

## 17. Unit tests

`./gradlew test` runs:
- `IndicatorsTest` — RSI/EMA/Williams %R/Marubozu/percentile-rank/OBV-slope/Momentum
  Ratio V2 sanity checks, plus (§20) a Wilder-vs-trailing-average ADX regression case
  with numbers from an independent reference computation
- `CandleAggregatorTest` — Checkpoint A/B timing, missing-data handling, and (§20) the
  5-minute candle close now firing the instant its 5th sub-candle is processed rather
  than one candle later, with an explicit no-double-fire check
- `ConflictResolverTest` — unanimous agreement, clear-winner conflict, and
  below-threshold conflict → no signal
- `CoreSignalEngineEntryRangeTest` — the exact boundary cases from spec section 50
  (price at 0%, +0.03%, -0.03%, and outside range) — unchanged by §20, this range is
  explicitly out of scope for that revision
- `FinancialModelTest` — win/loss PnL amounts, the tie-counts-as-Red rule, and (§20) the
  previously-untested tie-counts-as-Green case that let Bug 1.1 hide
- `StrategyRegistryTest` — parses the real `strategies_parameters.json` and asserts
  100% strategy-id coverage against the raw source file (spec sections 47-48), plus
  (§20) explicit-field-vs-text-heuristic coverage for `outcome_tie_counts_as_red`
- `DynamicScoreTest` (§20, new) — the overlap penalty, the statistical-confidence
  penalty, and the live/static credibility blend, all against an independent
  Python reference computation of the same formula

## 18. Final report

1. **Strategies found**: 31 (`strategies_parameters.json`) — 9 kept from the original
   27-strategy set, 22 added 2026-09 (see §19).
2. **Strategies implemented**: 31 — via the generic, JSON-driven `ComponentEvaluator` /
   `CoreSignalEngine`, not per-strategy hardcoded classes; coverage asserted by
   `StrategyRegistryTest`.
3. **Strategy coverage result**: 31 / 31 matched by automated test.
4. **Core Engine status**: implemented (`CoreSignalEngine.kt`), single shared instance
   used by both Live and Backtest.
5. **Live Engine status**: implemented (`LiveMonitoringService.kt`) — WebSocket ingest,
   warm-up backfill, reconnect + gap resync, Checkpoint A/B evaluation, Signal Lock,
   Room persistence, notification dispatch.
6. **Backtest Engine status**: implemented (`BacktestEngine.kt`) — historical REST
   klines, chronological replay through the same Core Signal Engine, 1/3/7/14/30/90-day
   periods.
7. **Notification status**: implemented — real Android notification channel, same
   canonical `Signal` object as the Live UI, duplicate protection via a `notified` flag
   in Room, deep-link tap-to-open.
8. **Background monitoring status**: implemented via foreground service +
   boot-restart receiver, subject to standard Android background execution limits
   (see "Known Android limitations").
9. **Unit test status**: 6 test files covering indicators, candle/checkpoint timing,
   conflict resolution, entry-range boundaries, the financial model, and strategy
   coverage — written and included, but **not executed** in this environment (no
   Android SDK / Gradle / network access available here; run `./gradlew test` in
   Android Studio to execute them).
10. **Build status**: **not compiled in this environment** (no Android SDK, Gradle, or
    network access to fetch dependencies here). The project was statically reviewed —
    package/directory consistency, brace/paren balance across all 43 Kotlin files, and
    every parsed-JSON-field cross-check — but a real `./gradlew assembleDebug` has not
    been run. Please treat the first build in Android Studio as part of setup.
11. **Final ZIP filename**: `BTCUSDT_Signal_Android_Project.zip`

**Limitation stated plainly**: acceptance criterion "Debug APK builds successfully" and
"installable on a real Android device" (spec sections 53, 59) could not be verified by
me — I do not have an Android build toolchain available. Everything else in the
acceptance list (strategy fidelity, no look-ahead bias, Checkpoint A/B timing, Signal
Lock, shared Core Signal Engine, canonical Signal object end-to-end, duplicate
notification protection, historical replay, unit tests present) has been implemented
and is ready for you to build and verify in Android Studio.

## 19. One-year re-evaluation (2026-09)

The original 27 strategies were selected/validated against a 90-day window
(2026-05-26 → 2026-08-24). A full year of real BTCUSDT 1-minute data
(2025-09-02 → 2026-09-02) was supplied for this revision — a year that, unlike the
original 90-day window, includes a ~54% peak-to-trough decline (Oct 2025 → Jul 2026)
and several sharp high-volatility legs, so it stress-tests the strategy set far more
than the original selection window did.

**Methodology.** A faithful line-for-line Python re-implementation of
`Indicators.kt` / `ComponentEvaluator.kt` / `MarketRegimeClassifier.kt` /
`ConflictResolver.kt` / `DynamicScore.kt` was built and validated two ways before being
trusted: (1) every indicator function was checked against a literal transliteration of
the Kotlin logic across many cut points (RSI, Stochastic, Williams %R, CCI, MACD,
ADX/DI, ATR, Bollinger %B, OBV-slope, Marubozu — exact match in every case), and (2) the
full 27-strategy roster was re-run standalone over the *original* 90-day window and
compared to the numbers already in this file's Strategy Database: aggregate win rate
matched to within 0.7 points (73.7% replica vs 74.5% documented) with a 0.78 rank
correlation across strategies — close enough to trust for the full-year analysis, not
so close that a residual methodology difference (most likely: the original numbers came
from a separate research-phase script, not literally this Kotlin engine) should be
hidden. New candidate strategies were selected on an 8-month in-sample slice
(2025-09-12 → 2026-05-01) and only kept if they *also* held up on a completely separate
~4-month out-of-sample slice (2026-05-01 → 2026-09-02) and specifically during
2025-10-01 → 2026-02-28 (the single steepest leg of the decline) — chronological
splits only, never shuffled, matching §4 item 4's existing walk-forward discipline.

**What was removed and why.** Running the existing 27-strategy roster's own
Checkpoint-A/B + entry-range + regime-gate logic (unchanged) over the full year showed
18 of 27 strategies at or below the 66.667% breakeven win rate the $0.50-win/$1.00-loss
model requires, or above breakeven only by a statistically negligible margin
(z < 0.5 vs. breakeven) with unstable month-to-month results. Every Trend_Bearish,
Vol_High, Vol_Medium, and Mom_StrongDown strategy fell in this group — the four
conditions a year with a 54% decline actually exercises hardest. The 9 kept strategies
(`STRAT-001/002/007/009/014/017/019/022/025`) all showed real, stable, full-year edges
and were kept with their original component logic untouched; only their reported
`performance` numbers were recomputed against the new 12-block (8 in-sample / 4
out-of-sample) walk-forward scheme documented in `meta.validation_methodology`.

**What was added.** 22 new strategies (`STRAT-N*`), 2–3 per regime that had zero or
weak coverage after the removals, built from the *same* 12 indicator primitives
`ComponentEvaluator` already supported (no new Kotlin was required for 21 of them) plus
one new primitive, `Momentum_Ratio_V2` (see below), used by `STRAT-N7A03`. Every one of
the 22 was rejected unless it cleared breakeven on the in-sample slice, the independent
out-of-sample slice, *and* the 2025-10 → 2026-02 crash sub-window — several
in-sample-only-strong combinations were found and discarded specifically because they
did not survive that OOS gate (see the delivery message for two concrete rejected
examples).

**Headline result** (combined engine — all strategies together, real
`ConflictResolver`/`DynamicScore`, one signal per 5m candle, run chronologically over
the full scored year, $100 start / $1 stake / +$0.50 win / -$1.00 loss, no change to any
of that financial model):

| | Old 27-strategy roster | New 31-strategy roster |
|---|---|---|
| Signals (355 scored days) | 4,855 (13.7/day) | 8,954 (25.2/day) |
| Win rate | 65.54% (**below breakeven**) | 68.34% |
| Total PnL | **-$82.00** | **+$224.50** |
| Final balance from $100 | $18.00 | $324.50 |

In plain terms: replayed honestly over the last real year, the *original* 27-strategy
roster would have lost money. The revised 31-strategy roster is solidly profitable over
the same year, including the crash months, without changing the entry-range rule,
the checkpoint timing, the financial model, or the conflict-resolution/scoring logic.

**New primitive: `Momentum_Ratio_V2`.** Added to `Indicators.kt` /
`ComponentEvaluator.kt` per an audit document's section 19 spec: `longRatio =
(Minute-1 High − 5M Open) / ATR(3, 5m, causal)`, `shortRatio = (5M Open − Minute-1 Low)
/ ATR(3, 5m, causal)`, direction fires GREEN/RED when one ratio clears the strategy's
`threshold` param and dominates the other side. Tested across 4 thresholds × 2
directional hypotheses × ~70 confirming-indicator pairings across every regime; the
large majority looked good in-sample and did not hold up out-of-sample (classic
overfitting signature) and were discarded. Exactly one combination
(`Momentum_Ratio_V2(0.6)` + `Bollinger_%B(20,2,5m)`, General/All regime, `STRAT-N7A03`)
held up in-sample, out-of-sample, and in the crash sub-window, and is the only strategy
using this primitive in the current roster. Two new `IndicatorsTest.kt` cases cover it.

**Not implemented — reported as unverified, not silently skipped.** A separate audit
document requested true continuous (sub-minute) monitoring and early signaling within
Minute 1/2, rather than the two discrete Checkpoint A/B evaluation points. §4 item 4
above already documents why the app implements exactly two checkpoints — the Strategy
Database itself defines only Checkpoint A/B, not a continuous-evaluation contract — and
that reasoning stands. Separately, and just as decisive practically: the only market
data available for this revision is 1-minute candles, so continuous sub-minute
evaluation cannot be backtested or validated at all with what's on hand (only "evaluate
at minute open" vs "evaluate at minute close" could even be tested, which is not what
was requested). Implementing it live without a way to validate it first would violate
this project's own repeated rule against unverified behavior changes. It is flagged here
as **UNVERIFIED / not implemented**, not silently dropped — genuinely enabling it would
need sub-minute (tick-level) historical data plus a validated redesign of
`CandleAggregator`/`CoreSignalEngine`'s checkpoint model, which is a larger, separate
piece of work.

**CI**: `.github/workflows/android-build.yml` was added (none existed in this project
before). It installs Gradle 8.7 directly rather than invoking `./gradlew`, because this
repo's zip export — as §6/§17 above already note — does not include
`gradle-wrapper.jar`; the workflow builds and unit-tests the app on every push without
needing that wrapper to be present.

## 20. Bug Report fixes + false-signal reduction + anti-obsolescence (2026-09)

A follow-up revision responding directly to `Bug_Report.txt` (a line-by-line audit of
the §19 codebase) plus three explicit additional asks: reduce the false/low-quality
signal rate **without** touching the ±0.03% entry range or the Checkpoint A/B (minute
1/2) timing — both confirmed still exactly as `CoreSignalEngineEntryRangeTest` and
`meta.hard_constraints`/`meta.signal_window` define them, and both untouched below;
sharpen live-market analysis precision; and give the engine a way to keep recalibrating
itself against the live market instead of quietly going stale as conditions drift from
the data it was last validated on.

**Every issue in `Bug_Report.txt` Parts 1-2 (the "must fix" and "should fix" items):**

| # | Issue | Fix |
|---|---|---|
| 1.1 | `outcomeTieCountsAsRed` had no effect — both `if`/`else` branches returned `Direction.RED` | `else` branch now returns `Direction.GREEN`; new test exercises the `false` case, which the old suite never did |
| 1.2 | The flag was derived from a fragile `"tie" in text && "Red" in text` heuristic that cannot detect negation | `meta.hard_constraints.outcome_tie_counts_as_red` is now an explicit JSON boolean, read directly; the old heuristic is kept only as a fallback for a database that predates the field |
| 1.3 | ADX used a plain trailing average of the last `period` DX values instead of Wilder's recursive smoothing | Fixed to seed-then-recursively-smooth exactly like `atrSeries` already does. Verified against the real full year of BTCUSDT 5m data supplied with this revision: mean absolute difference 3.93 (median 3.18, 90th pct 8.42), and **trend-regime classification flips on 10.02% of all 105,145 five-minute candles in the year** — directly gating which strategies are even eligible to fire at a given moment |
| 2.1 | `FiveMinuteCandleClosed` fired one candle late (only when the *next* bucket's first candle arrived), leaving the final signal of every backtest permanently `ACTIVE` and delaying live result resolution by a full minute | Now fires the instant the 5th sub-candle is processed. Verified with a standalone state-machine simulation: identical OHLCV aggregate, exactly one candle earlier, missing-data integrity unchanged |
| 2.2 | `evalStochastic`/`evalWilliamsR` ignored `hypothesis` entirely, unlike `evalRsi`/`evalCci` | Both now branch on `mean_reversion`/`momentum_continuation` the same way. Zero effect on the current 31-strategy roster (every existing Stochastic/Williams %R entry is already `mean_reversion`, confirmed by inspecting the JSON) — this only foreclosed a silent direction-inversion risk the day a differently-hypothesized instance is added. **Extra, disclosed beyond the report's own list:** `evalBollinger` had the identical gap and got the identical fix, for the identical reason |
| 3.1 | Gradle wrapper incomplete, project didn't build | `gradle/wrapper/gradle-wrapper.properties` now genuinely points at Gradle 8.7; `gradlew`/`gradlew.bat` added. The wrapper **jar** itself is a binary this sandbox has no network access to download — see updated §7 for the one remaining manual step |
| 3.2 | `Indicators.roc()`/`.sma()` dead code; `MarketRegimeClassifier` hand-duplicated the ROC formula instead of calling `Indicators.roc()` | Added `Indicators.rocSeries()`; `MarketRegimeClassifier.classifyMomentum` now calls it instead of maintaining a second copy. `.sma()` remains genuinely unused and was left alone (removing dead code that nothing else touches carried no signal-quality benefit) |
| 3.3 / 4.2 | Overlap penalty term always evaluated to `0.0` — two heavily-overlapping strategies that agreed got no penalty vs. two independent ones | Activated using the already-parsed `maxSignalOverlapPct`, capped at 0.5 points (same scale as the existing z-score term) — see below |
| 3.5 | `adxDi`/`macd` required one candle more than actually necessary before returning a value | Both boundary checks relaxed to the true minimum |
| 3.7 / 4.5 | Backtest replayed all the way to `System.currentTimeMillis()`, so a signal could be issued against the currently-forming candle and never get a chance to resolve inside the run | `BacktestEngine.run()` now rounds its end boundary down to the last fully-closed 5-minute candle; `BinanceRestClient.getKlines` independently never returns a candle that hasn't actually closed yet, as a second, defense-in-depth layer covering this same call site plus live warm-up/gap-resync |
| 4.3 | 14 of 31 strategies (45%) have a z-score below the 1.645 one-sided-95%-confidence threshold — not statistically distinguishable from a coin flip against breakeven | See below — implemented as a soft, continuous discount, not the report's alternative of excluding them outright |
| 4.6 | `adxDi` (exactly where the 1.3 bug was hiding), `stochastic`, `cci`, `macd`, `bollingerPercentB` had no unit tests | Added for `adxDi`; the others were out of scope for this pass (no bug was found in their logic — 1.3 was specific to the ADX averaging step) |

Item 4.4 (selection-bias caution: the 31 strategies were themselves chosen using
performance on data that overlaps what any in-app Backtest run would replay) is a
methodology note, not a code change, and stands as documented in the report.

**Reducing false signals without touching the ±0.03% range or the two-checkpoint
timing.** `DynamicScore.compute` (the meta-layer that scores an *already-fired,
already-in-range* strategy against another one when they disagree — see
`ConflictResolver`) picked up two new terms:

- **Overlap penalty** (`OVERLAP_PENALTY_MAX = 0.5`): `0.5 * (maxSignalOverlapPct / 100)`.
  A strategy that fires in near-lockstep with several others is not really independent
  corroborating evidence, so it is worth proportionally less in a conflict.
- **Statistical-confidence penalty** (`STATISTICAL_UNCERTAINTY_PENALTY_MAX = 0.5`): a
  linear ramp from `0.5` at z ≤ 0 down to `0` at z ≥ 1.645. The report's own alternative
  — excluding the 14 weak-z strategies outright — was deliberately not taken: it would
  have cut deep into genuine positive signal volume, which this revision was explicitly
  asked not to do. Because `ConflictResolver` only ever consults a strategy's score when
  it is competing against a *different-direction* vote from another strategy (a lone,
  uncontested strategy wins regardless of score — see `ConflictResolver.kt`), this
  penalty only ever changes the outcome of genuine disagreements: it makes a
  statistically weak strategy less likely to overrule a statistically solid one, without
  reducing the signal count of every strategy that fires unopposed.

Simulated against all 31 real strategies (spot-checked, not shipped as a test): scores
shift by a fraction of a point each, a handful of strategies re-rank by a few places —
most sharply, a low-overlap strategy (12.2%) climbs from rank 15 to rank 7, and a
100%-overlap strategy drops from rank 6 to 9 — with no score reaching zero and no
wholesale reordering.

**More precise live-market analysis.**
- `BinanceRestClient.getKlines` now enforces, in code, the "never return a candle that
  hasn't actually closed" guarantee its own docstring already claimed but didn't
  actually implement (every returned row was unconditionally marked `isClosed = true`).
  This closes a real no-look-ahead gap in three call sites at once: `BacktestEngine`'s
  historical fetch, and `LiveMonitoringService`'s `warmUp()` and `resyncGap()`, both of
  which can legitimately query up to "now."
- The Bug 2.1 fix above also means live Checkpoint results and DB writes now land at the
  true candle-close moment instead of lagging it by up to a minute — `LiveEngineState`'s
  price-snapshot-freeze comment has been updated to describe why it is still needed
  (WebSocket message ordering between two adjacent candles isn't guaranteed) now that
  the reason is no longer "compensate for a minute of drift."

**Preventing the strategy set and engine from going stale (anti-obsolescence).**
`RecentWindowStats` now carries a live z-score (`DynamicScore.zScoreVsBreakeven` — the
same one-proportion z-test used to produce the Strategy Database's own
`oosZScoreVsBreakeven` numbers and the report's own 4.3 analysis, applied to a rolling
window's win/loss record instead of the one-time backtest). `DynamicScore.compute`
blends this, and the rolling PnL, with the static Strategy Database numbers using a
credibility weight `n / (n + 30)` that shifts smoothly from "trust the one-time backtest
snapshot" toward "trust this strategy's own live track record" as real resolved signals
accumulate — replacing the previous on/off switch, which handed a strategy's *entire*
score over to a raw, unweighted average the instant a single live signal resolved (a
real source of score noise this revision found: one early win or loss could swing a
score far more than a long OOS record ever would). Concretely: a strategy whose edge
quietly decays as the live market drifts from the conditions it was validated on will
see its own blended z fall and its statistical-confidence penalty rise automatically —
no manual re-running of the research pipeline required — while a strategy that keeps
performing keeps its full score. `BacktestEngine`'s own rolling stats were extended the
same way, so Live and Backtest keep scoring identically (this class's own
no-second-implementation rule).

**What this section does *not* claim.** Unlike §19, no full old-vs-new *combined-engine*
backtest (all 31 strategies, real `ConflictResolver`/`DynamicScore`, run chronologically
over the whole year) was produced for this revision — doing that credibly would mean
either compiling and running the actual Kotlin project (no Android SDK/Gradle/network
access in the environment these changes were made in) or hand-porting the entire
31-strategy `ComponentEvaluator` logic to a second language the way §19's methodology
did, which was out of scope alongside everything else in this pass. The ADX regime-flip
number above (10.02% of candles) is real, measured against the actual supplied year of
data with an independently-written reference implementation — but the end-to-end effect
of the scoring changes on total signal count and win rate has **not** been measured this
way, only sanity-checked per-strategy as described above. Once built, running this
app's own **Backtest** screen over a representative period is the authoritative way to
see this revision's real effect — Backtest and Live now share every piece of this
change, including the boundary-alignment fix, so its numbers should be trustworthy in a
way they previously were not (§3.7/4.5).

**Files touched**: `CoreSignalEngine.kt`, `StrategyRegistry.kt`, `Indicators.kt`,
`CandleAggregator.kt`, `ComponentEvaluator.kt`, `MarketRegimeClassifier.kt`,
`DynamicScore.kt`, `SignalRepository.kt`, `LiveMonitoringService.kt`,
`BacktestEngine.kt`, `BinanceRestClient.kt`, `LiveEngineState.kt`,
`strategies_parameters.json` (+ its test-resources copy), `gradle-wrapper.properties`,
`gradlew`, `gradlew.bat`, and the test files listed in §17.


## 21. Reversal-Zone secondary entry (minute 3 scan)

A user-requested execution-layer feature, not a new discovered strategy (no file under
"Strategy fidelity" §3 was touched, and `strategies_parameters.json` is unmodified):
once a primary Checkpoint A/B signal has locked for a candle, the engine now keeps
watching through the whole of minute 3 (t+2min -> t+3min) for a second, independent
re-entry opportunity on the side of candle-open opposite the primary's own entry range —
e.g. a primary GREEN signal (entered in the usual 0%..+0.03% range) watches for the price
dipping down into -0.03%..-0.10% from candle open; a primary RED signal mirrors this on
the positive side. This second signal's direction is always the SAME as the primary's —
a same-direction re-entry during a pullback, confirmed explicitly over chat ("نتیجه درست
برابر است با جهت تشخیص داده شده تا دقیقه دوم") — never a reversed bet.

**Firing rule** (`engine/ReversalZoneScanner.kt`, exactly as specified over chat):
1. The first tick where price enters the zone arms a 10-second watch timer — it does not
   fire immediately.
2. While that timer runs, any later tick that pushes the price deeper into the zone than
   every tick since the touch (e.g. -0.05% then -0.08%) fires immediately at that price.
3. If 10 seconds pass with no new extreme, it fires at whatever price is current then, as
   long as it's still inside the zone.
4. If price leaves the zone before either 2 or 3 fires, that touch is discarded and
   scanning re-arms for a fresh touch later in the same window.
5. At most one secondary signal per candle; firing is never deferred to the end of
   minute 3 — it can happen as early as t+2:30 or any other point in the window.

Represented as a new `Checkpoint.C` value alongside the existing A/B (see `MarketModels.kt`
— nothing in the codebase pattern-matched exhaustively over `Checkpoint`, so this is a
non-breaking addition). `CoreSignalEngine.evaluateResult` picks its financial model based
on this: A/B keep the Strategy Database's own +$0.5/-$1 model; `Checkpoint.C` always uses
its own, separate +$2/-$1 model (`ReversalZoneConfig`), regardless of what the database
says — the win/lose direction check itself (final close vs. candle open, tie = Red) is
identical for every checkpoint.

**Live**: `LiveMonitoringService` owns one `ReversalZoneScanner` per in-progress candle,
armed the instant a primary locks, fed every WebSocket tick unconditionally (the scanner
itself no-ops outside its armed window). A fired secondary is saved and notified exactly
like a primary signal, and shown in its own card on the Live screen
(`LiveEngineState.secondarySignal`). Because a candle can now carry two still-ACTIVE
signals at once, `handleCandleClosed` was changed to resolve *every* active signal for
that candle (`SignalDao.getActiveLiveSignalsForCandle`) instead of only the single
"most recent active" row — the old query would have permanently stranded the primary's
`ACTIVE` status the moment a secondary fired after it.

**Backtest**: historical klines are only 1-minute OHLC bars, not the tick-by-tick path
Live scans with a real 10-second timer. `BacktestEngine` approximates minute 3 with a
synthetic 4-point intra-minute path (open, the two extremes ordered by which more
plausibly came first given how the candle resolved, close) run through the identical
`ReversalZoneScanner`, and reports the results as their own `reversalZoneSignals`/
`reversalZoneWins`/`reversalZoneLosses`/`reversalZonePnlUsd` fields on `BacktestSummary`
— kept separate from the primary `wins`/`losses`/`totalPnlUsd`, the same way the app's
existing nexa/magic dual-engine reporting keeps each stream distinct, both because the
financial model differs and because this reconstruction is a stated approximation, not
real tick data. Rows are still saved to History/Performance alongside primary signals,
tagged `Checkpoint.C` / `activeStrategyId = "REVERSAL_ZONE"`.

**One assumption made, not explicitly confirmed over chat**: the +$2/-$1 model applies
only to Checkpoint C signals; the primary A/B financial model (+$0.5/-$1, unchanged) was
left alone rather than globally replaced. Flagged here in case that's not what was meant.

**Follow-up (same handoff): notifications scoped to the Reversal-Zone signal only.** A
primary A/B signal locking no longer posts a push notification on its own — it is still
computed, saved, shown on the Live screen, and used to arm the Reversal-Zone scan exactly
as before, it just stays silent. The only push notification per candle now comes from a
fired Checkpoint C (Reversal-Zone) signal; a candle where the minute-3 scan never fires
produces no notification at all. The always-on foreground-service status notification
(persistent "Signal locked: ..." text) is unrelated to this and still updates as before —
this change is specifically about the per-signal alert (`NotificationHelper.notifySignal`).

**Files touched**: `MarketModels.kt` (new `Checkpoint.C`), `ReversalZoneScanner.kt` (new),
`CoreSignalEngine.kt`, `LiveEngineState.kt`, `LiveMonitoringService.kt`, `SignalDao.kt`,
`SignalRepository.kt`, `BacktestEngine.kt`, `LiveSignalScreen.kt`, plus
`ReversalZoneScannerTest.kt` (new) and two new cases in `FinancialModelTest.kt`.


## 22. Reversal-Zone total/correct/incorrect tallies, surfaced on Performance and Backtest

User request (chat handoff): "تعداد کل و نتیجه درست و غلط هم برای لایو و هم بک تست فقط
بر اساس سیگنال ریورسال دقیقه ۲ تا ۳ ثبت و شمارش شود" — the Reversal-Zone (minute-2-to-3,
Checkpoint C) signal needed its own recorded total / correct (Won) / incorrect (Lost)
count, for both Live and Backtest. Both engines already *recorded* every Reversal-Zone
fire as a `Signal` row (§21), but nothing counted them on their own:

- **Backtest**: `BacktestEngine` already computed `reversalZoneSignals`/`reversalZoneWins`/
  `reversalZoneLosses`/`reversalZonePnlUsd` on `BacktestSummary`, but `BacktestScreen` never
  displayed them. Added a "Reversal-Zone Re-entries (Minute 2-3)" card (Total, Win Rate,
  Correct/Incorrect, PnL) right below the existing Wins/Losses row, reading those
  already-computed fields — no engine change needed.
- **Live**: `PerformanceScreen` had no equivalent split at all — its "Total Signals" /
  "Wins" / "Losses" queried `SignalRepository.getLiveSince` unfiltered, which silently
  folded `activeStrategyId = "REVERSAL_ZONE"` rows into those primary counts (a different
  +$2/-$1 financial model getting mixed into numbers that were supposed to mean "primary
  A/B signals only" — the same failure mode §21's Backtest section explicitly calls out
  avoiding). Fixed by splitting the fetched rows into primary vs. Reversal-Zone by
  `activeStrategyId` before computing anything, so the existing Total/Win-Rate/PnL/
  Best-Worst-Strategy metrics now reflect primary signals exactly as they always were
  meant to, and a new matching "Reversal-Zone Re-entries (Minute 2-3)" card shows the
  Reversal-Zone-only Total/Correct/Incorrect/PnL alongside it, same period filter as the
  rest of the screen.

Both cards read "Correct (Won)" / "Incorrect (Lost)" rather than "Wins"/"Losses" to match
the user's own wording ("نتیجه درست و غلط"). No engine, DAO, or persistence changes were
needed — both signal streams were already being recorded correctly; this was purely a
counting/display gap (and, on the Live side, a mixing bug).

**Files touched**: `PerformanceScreen.kt`, `BacktestScreen.kt`.


## 23. Rev Green / Rev Red — configurable Reversal-Zone ranges

User request (chat handoff): "بازه عددی ریورسال برای سیگنال سبز -0.03 تا -0.1 و برای
قرمز +0.03 تا 0.1 است، میخواهم در تنظیمات rev green، rev red مشخص کنی و این اعداد قابل
تغییر باشند و با زدن دکمه save شوند، تغییر باید روی بک تست و لایو نشان داده شود" — the
Reversal-Zone (minute-2-to-3) zone edges, previously hardcoded at 0.03%/0.10% for both
colors via a single shared `innerThresholdPct`/`outerBoundPct` pair on `ReversalZoneConfig`
(§21), needed to become user-editable per color, saved explicitly via a button, and
applied on both Live and Backtest.

- **`ReversalZoneConfig`** (`ReversalZoneScanner.kt`): split into four independent fields
  — `greenInnerPct`/`greenOuterPct` (Green zone: -Inner% to -Outer%) and
  `redInnerPct`/`redOuterPct` (Red zone: +Inner% to +Outer%) — same shipped defaults
  (0.03/0.10 each side) so nobody who never opens Settings sees any behavior change.
  `ReversalZoneScanner.onTick`'s zone check now reads the matching pair for the primary's
  own direction instead of one shared pair mirrored by sign.
- **Settings** (`SettingsRepository.kt` + `SettingsScreen.kt`): four new persisted
  `AppSettings` fields (DataStore `doublePreferencesKey`s), plus a new "Rev Green" / "Rev
  Red" card with a Start/End numeric field per color, a live preview of the resulting
  signed zone, and a single **Save** button. Editing does NOT write through immediately —
  local text state only, validated (all four parse as numbers, all > 0, Start < End per
  color) and persisted together in one `SettingsRepository.setReversalZoneRanges(...)`
  call only when Save is tapped, exactly as asked. Values are NOT bound live to
  `settingsFlow` the way the notification switches are, specifically so typing a second
  digit doesn't get clobbered by a DataStore round-trip mid-keystroke.
- **Live** (`LiveMonitoringService.kt`): `onKlineUpdate`'s new-candle branch — a plain,
  non-suspend callback — builds each candle's fresh `ReversalZoneScanner` from a
  `@Volatile reversalZoneConfig` field instead of `ReversalZoneConfig()`'s defaults. That
  field is kept current by a dedicated `settingsRepo.settingsFlow.collect` coroutine
  started in `onCreate()`, so a value Saved on the Settings screen takes effect starting
  with the next 5-minute candle boundary (a candle already in progress keeps whatever
  config its own scanner was built with — same rule as every other per-candle engine
  state in this class).
- **Backtest** (`BacktestEngine.kt` / `BacktestState.kt`): `BacktestEngine.run` gained a
  `reversalZoneConfig: ReversalZoneConfig` parameter (default unchanged), threaded into
  the per-candle `ReversalZoneScanner` in the minute-3 replay scan. `BacktestState.start`
  reads the current Rev Green/Rev Red settings alongside the existing blocked-strategy
  read and passes them through, so a Saved value is picked up by the very next backtest
  run (not retroactively — an already-*displayed* past run's numbers don't change).

**Files touched**: `ReversalZoneScanner.kt`, `SettingsRepository.kt`, `SettingsScreen.kt`,
`LiveMonitoringService.kt`, `BacktestEngine.kt`, `BacktestState.kt`.

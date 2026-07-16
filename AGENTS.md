# AGENTS.md — Session Startup Guide

**Project:** Shamshir — Prop-firm algorithmic trading engine (.NET 10, C# 13)
**Branch:** `iter/alpha-loop`
**Created:** 2026-06-18
**Updated:** 2026-07-10 (iter-alpha-loop r0 — session setup)

---

## Read this first (mandatory, in order)

At the start of every session:

1. **`docs/iterations/iter-alpha-loop/TRACKER.md`** — Current state + handoff block
2. **`docs/WORKFLOW.md`** — Agent workflow rules, code standards (current active workflow)
3. **`conductor-DEBT.md`** — Open debt items
4. **`docs/iterations/iter-alpha-loop/PLAN.md`** — Master plan (R0→R5 + verification matrix)
5. **`docs/iterations/iter-parity-pipeline/AUDIT.md`** — Evidence audit (F1-F16, R1-R10) — historical
6. **`docs/reference/SYSTEM-REFERENCE.md`** — System overview
7. **`docs/reference/CODE-MAP.md`** — Feature→file index
8. **`docs/reference/BACKTEST-ARCHITECTURE.md`** — Venue backtest paths
9. **`docs/reference/TEST-ARCHITECTURE.md`** — Test tiers + harnesses
10. **`DECISIONS.md`** — All resolved decisions (D1-D97)
11. **`docs/audit/RECONCILE-FINDINGS.md`** — Fidelity gaps + run templates
12. **`docs/CTRADER-TEST-POLICY.md`** — cTrader test triage

**cTrader credentials are accessible to the agent.** The historic "needs creds" belief was from deadlock bugs (B1-B3, now fixed). Credentials: CtId=seankiaa, **Account=5834367**, PwdFile=ctrader.pwd. The cTrader path is functional. See `docs/agents/ctrader-quickstart.md`.

**Before any venue/parity investigation, read `docs/reference/INVESTIGATION-METHOD.md`.** It is normative,
not advisory. It exists because four consecutive sessions — all with green gates — fixed real bugs and
still missed the actual cause. Short version: *make the venue tell you what it did; do not infer it from
what happened afterwards.* Green credential-free gates (Unit/Integration/Sim-fast) **never** support a
claim about cTrader — none of them place an order at a venue.

**cTrader is the oracle; the tape is a mimic of it.** When they disagree, the tape is what changes —
unless the venue's behaviour is our own bug driving it (F38: we were feeding it stale bars).

**Account currency is one config value** (`Account:Currency`, default USD). It stamps every `SymbolInfo`,
decides which cross-rate legs a run loads, and is checked against the currency the venue declares — a
mismatch is reported on the run. Cross rates are a USD-pivot table fed from market data; a missing leg
fails the run rather than defaulting (a wrong cross rate is a wrong lot size).

## Build and test

```powershell
dotnet build                                 # Full build
dotnet test tests/TradingEngine.Tests.Unit   # Unit tests (716 pass, 6 skip)
dotnet test tests/TradingEngine.Tests.Simulation  # Simulation/FTMO tests (144 pass)
dotnet test tests/TradingEngine.Tests.Integration  # Integration tests (121 pass)
```

## Architecture at a glance

```
src/
  TradingEngine.Domain/          # Pure domain — zero infra deps
  TradingEngine.Application/     # Assembly marker only
  TradingEngine.Infrastructure/  # EF Core, Skender, adapters, persistence
  TradingEngine.Risk/            # Risk engine, position sizing, prop firm rules
  TradingEngine.Strategies/    # Strategy implementations
  TradingEngine.Services/      # PipCalc, SL/TP, trailing, EntryPlanner, TradeCost, ExitLab
  TradingEngine.Host/          # EngineWorker, DI wiring, Program.cs
  TradingEngine.Web/             # Razor Pages, API controllers, SSE/SignalR
  TradingEngine.Adapters.CTrader/ # C# 6 cBot (cTrader integration)
  TradingEngine.Engine/          # Kernel engine (EngineReducer, EngineState)
tests/
  TradingEngine.Tests.Unit/      # xUnit, isolated
  TradingEngine.Tests.Simulation/ # End-to-end backtest
  TradingEngine.Tests.Integration/ # EF Core + SQLite integration tests
```

## Key facts

- **Three venue paths:** `BacktestReplayAdapter` (credential-free, per-run bars from DB), `TapeReplayAdapter` (fast, from `marketdata.db`), and `CTraderBrokerAdapter` (cTrader NetMQ). Default is replay.
- **All money math in `decimal`** — `double` only at Skender indicator boundaries.
- **Lot sizing uses `Math.Floor`, never `Math.Round`.**
- **Schema via EF migrations only** — no raw SQL `ALTER TABLE`.
- **`CancellationToken` as last parameter on every async method.**
- **`BoundedChannelFullMode.Wait`** for order/trade channels; `DropOldest` only for analytics.
- **`IEngineClock`** for all time — never `DateTime.UtcNow` directly.

## Current state (iter/parity-pipeline — P0-P7 COMPLETE, 2026-07-10)

The parity-pipeline iteration is fully delivered. All P0-P6 phases completed, all 8 P7 sessions done.
The working tree was landed and squashed into `develop` (06adecf). 18 stale local branches deleted,
mdtape remote removed, docs cleaned and reconciled.

Key deliverables:
- **P0:** Parity truth — sizing (F1), status truth (F5), trade persistence (F6), entry latency (F2)
- **P1:** One database (F10) + config propagation (F9)
- **P2:** Run lifecycle state machine (F8) + compare-both
- **P3:** ResearchCli pipeline — HTTP driver, playbooks, exit lab, walk-forward
- **P4:** Exploration funnel (F11), MAE/MFE units doctrine (F12), reference scales
- **P5:** UI truth — equity (F13), start button (F15), compare-both visibility (F16)
- **P6:** Data quality sentinel, session fingerprinting, spread/vol filter, regime calibration, block bootstrap, meta-allocator, entry quality
- **P7:** Live verification, cTrader proof, traps 1-6, compare-both gate, F6-R economics, cTrader audit, final audit
- **A1:** F17 fix — kernel event persistence verified; docs cleaned up

## QA protocol (added 2026-07-09 — saves tokens on clean sessions)
- Skip previous-session QA when the last session ended `advanced` or `progress` with all gates green.
- Run full QA only when last session was `gatesRed`, `stalled`, `noProgress`, or `interrupted`.

## Tracker update rule
After every session, update BOTH the handoff block AND the checkpoint row in TRACKER.md. The row must show `DONE`, the commit hash, and evidence path. If only the handoff changes, Conductor re-reads the same TODO row and launches a duplicate session.

## What's next

See `docs/iterations/iter-alpha-loop/PLAN.md`. The next iteration is **iter-alpha-loop** —
closing the research loop with portfolio-level automation, entry lab productionization, and
regime-conditioned execution.

---

## P6 session bugs found + fixes (2026-07-06)

### B1 — Compare-both config deserialization ignores dates (FIXED)

**File:** `src/TradingEngine.Web/Api/RunsController.cs:211`
**Root cause:** `JsonSerializer.Deserialize<StartRunRequest>(json)` without `PropertyNameCaseInsensitive`.
The pinned config files use lowercase `"start"`/`"end"` but the DTO has `Start`/`End`. Default STJ is
case-sensitive → dates fall through to defaults (`2024-01-01`) where no data exists → "No bars found."
**Fix:** Added `new JsonSerializerOptions { PropertyNameCaseInsensitive = true }` to deserialization call.
**Verified:** Build succeeds. Not runtime-verified (compare-both never completed due to B3 below).

### B2 — cTrader stuck-running deadlock (FIXED, PARTIALLY VERIFIED)

**Files:**
- `src/TradingEngine.Infrastructure/Venues/CTrader/CTraderBrokerAdapter.cs:110-255` (ReadSubLoop, ReadRouterLoop)
- `src/TradingEngine.Web/Services/BacktestOrchestrator.cs:1290-1300` (RunEngineNetMqAsync finally block)

**Root cause:** `RunEngineNetMqAsync`'s `finally` block sequence after CLI exit:
1. `await adapter.BarStream.Completion;` → waits FOREVER
2. `await innerHost.StopAsync(CancellationToken.None);` → never reached
3. `await DisposeHostAsync(innerHost);` → never reached (this calls `DisconnectAsync` which completes channels)

Why: `BarStream.Completion` fires only when `_barChannel.Writer.Complete()` is called. That only
happens in `CTraderBrokerAdapter.DisconnectAsync()` (line 98). `DisconnectAsync` is only called via
`DisposeHostAsync` at step 3 — AFTER step 1. Classic circular deadlock.

**Evidence:** DB row `0db44736` had `CompletedAtUtc = 0001-01-01`, `ExitCode = -1` — the orchestrator
never wrote the end record. Tape leg (`1a696c1a`) completed normally (11 trades).

**Fixes applied (2 layers):**

1. **Adapter layer:** `ReadRouterLoop` now has a `finally` block that calls `_barChannel.Writer.TryComplete()`
   and `_execChannel.Writer.TryComplete()`. `ReadSubLoop` completes `_tickChannel` and `_accountChannel`.
   When the cTrader CLI exits, the transport disconnects, the read loops exit naturally, and the channels
   are marked complete — so `BarStream.Completion` fires without needing `DisconnectAsync` first.

2. **Orchestrator safety net:** `RunEngineNetMqAsync`'s `finally` block now wraps `BarStream.Completion`
   with a 30-second timeout. On timeout, forces `adapter.DisconnectAsync()` to unblock.

**To verify:** Run a standalone cTrader backtest (not compare-both) and confirm the run status reaches
"completed" or "failed" within the 30-min timeout (should complete in ~60-90s for a short window).
Previous stuck runs would hang indefinitely at "running."

### B3 — Compare-both recursive invocation (FIXED, NOT VERIFIED)

**File:** `src/TradingEngine.Web/Services/BacktestOrchestrator.cs:795-844`

**Root cause:** `RunCompareBothAsync` creates the cTrader child config by copying the parent's
`CustomParams` dict. The parent has `["Compare"] = "both"` (set in `RunsController.CompareBoth`).
When `Start(ctraderCfg)` is called → `RunAsync` detects `compareBoth=true` → calls
`RunCompareBothAsync` recursively for the child. Meanwhile the outer `RunCompareBothAsync`
calls `RunEngineNetMqAsync` for the SAME runId. Two concurrent cTrader runs colliding.

**Evidence:** Error "The given key '71dc6285' was not present in the dictionary" at 5s into run —
the recursive call's tape runner or state manipulation collided with the outer call.

**Two-part fix:**

1. `ctraderCfg.CustomParams.Remove("Compare")` — prevents the child's `RunAsync` from detecting
   compare-both mode.

2. Manually register `ctraderState` via `_runs[ctraderRunId] = new BacktestRunState { RunId = ctraderRunId }`
   instead of calling `Start(ctraderCfg)`. `Start()` spawns `RunAsync` as a background task, which
   would see `Venue="ctrader"` and run a duplicate `RunEngineNetMqAsync`. The manual registration
   skips the background task — RunCompareBothAsync owns the cTrader leg lifecycle directly.

3. Also fixed: `tapeCfg = cfg` (shallow copy mutating original) → `cfg with { CustomParams = new Dict(cfg.CustomParams) { ["Venue"] = "tape" } }`.

---

## Session struggle log

1. **Windows PowerShell quoting:** `curl.exe` with JSON payloads fails with `Invalid start of property name`.
   Must use PowerShell `Invoke-RestMethod` with `$body = '{"key":"value"}'` (single quotes around JSON).

2. **App output noise:** EF Core Debug-level logging floods the terminal with query compilation trees
   (thousands of lines per request). Makes it impossible to see the actual run's progress log lines.
   **Recommendation:** Set `Logging:LogLevel:Microsoft.EntityFrameworkCore` to `Warning` in
   `appsettings.Development.json` when iterating on the API.

3. **Process killing on Windows:** `Get-Process -Name "dotnet" | ForEach-Object { Stop-Process -Id $_.Id -Force }`
   is the reliable pattern. CIM/WMI (`Get-CimInstance`) has PowerShell escaping issues with `$_.ProcessId`.

4. **Build-lock race:** When the app is running and `dotnet build` tries to overwrite output files,
   MSB3021/MSB3027 errors. Kill all dotnet processes first, then build.

5. **Compare-both untested end-to-end:** Despite 4+ fix-build-restart-test cycles, never got a
   successful compare-both run. The 3 bugs (B1, B2, B3) were progressively discovered and fixed.
   The fixes are structurally correct (each traced through the full call chain, not guessed) but
   require a clean end-to-end verify: start app, POST compare-both, poll to terminal, GET reconcile.

---

## cTrader CLI / background backtests — findings

**The deadlock problem:** When the cTrader CLI process exits, the engine's `ReadRouterLoop` ends but
the bar channel writer is never marked complete. The orchestrator's shutdown sequence awaits
`BarStream.Completion` before ever calling `DisconnectAsync` (which is the only place the channel
writer IS completed). Fix: B2 above completes channels in the read loop's `finally` block.

**Background cTrader runs:** The infrastructure already supports them — `RunAsync` is spawned via
`Task.Run`, and all runs share the same `_runs` dictionary. The UI polls `GET /api/runs/{id}` for
status. The stuck-run bug meant the cTrader leg never reached a terminal state, which blocked the UI
(no "stuck" detection). With B2 fixed, runs should complete or fail within the 30-min timeout.

**CLI hanging is NOT a CliWrap issue.** The `CTraderCli.BacktestAsync` call returns correctly when
the CLI process exits. The hang is purely in the engine-side shutdown sequence (B2). No CliWrap
changes needed.

**To improve reliability further (P6.3):**
- The 30-minute linked CTS timeout catches hung `BacktestAsync` calls (CLI stalls)
- The 30-second `BarStream.Completion` safety timeout catches hung channel completions
- Orphan process reaping already exists at lines 1301-1364

---

## Rules you must not break

1. `decimal` for all price, money, lot arithmetic
2. Never add infrastructure deps to `TradingEngine.Domain`
3. Schema changes via EF migrations only
4. No `Console.WriteLine` — Serilog message templates only
5. Don't touch `aspire/AppHost` (NU1903)
6. Keep Unit + Simulation + Integration suites green — stop-the-line on red
7. Golden must stay 63/63 byte-identical (kernel untouched)
8. When driving the web app: kill all dotnet processes before rebuilding (MSB3021 lock)
9. Use `Invoke-RestMethod` for API calls, not `curl.exe` (Windows quoting)
10. The app's cwd MUST be `src/TradingEngine.Web` so it finds `data/trading.db` and `wwwroot`

---

## Research integrity — the rules that were broken (added 2026-07-11)

Every rule below was written because it was violated in the R1/R2 sessions, and each violation
survived review because the session *sounded* rigorous. Read `docs/iterations/iter-alpha-loop/PARITY-TRUTH.md`
for the full autopsy. These are not style preferences — each one silently corrupted a result.

**R1. Units and signs before stories.** When two systems report different numbers, verify the units,
the sign convention, and the formula *before* proposing any explanation about the world. The R2 session
found tape swap `+5.40` vs cTrader `−246.20` and wrote a paragraph about the Bank of Canada's rate
differential. The truth was that the two venues store costs with opposite signs. **A domain narrative
that explains a discrepancy you have not yet traced to a line of code is a guess wearing a suit.**

**R2. A pre-registered gate is not negotiable by the agent that trips it.** R2's plan said: if trade
counts differ by >20%, STOP and escalate. Counts differed by 33%. The session ran three more window
variants until the number looked acceptable, then argued the threshold was "a function of window
length". If a gate fires: STOP, write down what fired, hand it to the owner. Changing the measurement
until the gate passes is the single most expensive thing you can do here, because the result *looks*
like progress.

**R3. Any claim about persisted state must carry the query that proves it.** The R1 scoreboard says
"248 below-floor cells: all have valid reasons recorded." `SELECT COUNT(*) FROM ExperimentRuns` returns
**4**. Do not write "persisted", "recorded", "scored", or "committed" without pasting the query and its
output into the evidence file. The PLAN's truth gates are SQL for exactly this reason — **run them, and
paste the result, even when you are sure.**

**R4. Never change the statistical unit without pre-registering it.** R1's plan was 252 cells. R1 ran
28 backtests with 9 strategies commingled in one account, then sliced them into "cells" — so the
strategies competed for one risk budget and 40% of every score came from a shared equity curve.
Batching that changes what a row *means* is a design change, not an optimisation. Flag it and stop.

**R5. Validate a model fix against the oracle with arithmetic, before you ship it.** The
`commissionPerMillion` change was never checked against a single cTrader number. One division would
have caught it: cTrader charged $54.36 on 15 XAUUSD trades; the new formula produces $0.006 per lot.
It is exact only for USD-base pairs, which is why it looked right on USDCAD. **If you "fix" a money
model, compute what it predicts for a trade you already have a venue number for, and compare.**

**R6. A surprising result is a bug report, not a footnote.** 248 of 252 cells failing a 20-trade floor
over ten months is not "the floor is restrictive" — it is nine strategies barely firing, and it needed
an investigation, not a bullet point. When the data surprises you, that is the finding. Chase it.

**R7. Fix the cause, don't scope the symptom away.** The `TRADES_PARTIALLY_UNRECONSTRUCTABLE` barrier
was scoped to `venue=ctrader` (`BacktestOrchestrator.cs:522`) instead of having its journal pairing
fixed — so now every cTrader run is stored with a warning and we have learned to ignore warnings.
Suppressing a signal is worse than the bug, because it costs you the signal too.

**R8. No hardcoded fudge factors in the money model, ever.** If the tape disagrees with cTrader, the
fix is to make the venue *declare* the number (D10) and correct our formula. Tuning a constant until
the two agree destroys the only oracle we have.

---

## Dev-cycle speed rules (added 2026-07-15 — from the X2/X3 retrospective)

The X2/X3 session lost ~50 min to tooling, not thinking. Backlog to fix it:
`docs/iterations/iter-dx-speed/PLAN.md` (D0–D6). Until/beyond that lands:

1. **One PLAN-budgeted phase per session.** Bundling two phases more than doubles the survey and
   verification surface — X2+X3 together is why that session ran long.
2. **Run long suites in the background** (full Playwright, full builds) while you write tracker /
   ledger / evidence updates. Never sit idle on a 7-minute suite.
3. **Playwright has ~15 pre-existing failures on a healthy tree** — see the shamshir-ui skill.
   Iterate on a targeted spec (~30s), full suite once before "done". Never stash-rebuild a baseline
   to prove a UI test failure is pre-existing; `web-ui/tests/e2e/KNOWN-FAILURES.md` (or the skill
   note until it exists) is the record.
4. **Bank every environment fact the session cost you a probe to learn** into the matching
   `.claude/skills/*/SKILL.md` in the SAME session (API removals, table names, CLI flags, cold
   endpoints). Re-derivation is the silent tax.
5. **Write braces on every `if`** — IDE0011 is promoted to a build error and only surfaces at the
   end of a full build.
6. What this must never speed away: the live compare-both doctrine, analyzer severities, the full
   e2e suite's existence, and the credential-free gate baseline (see iter-dx-speed V1–V5).

## RESUME (overwrite this block each session)

**Phase:** **iter-viability OPEN (2026-07-16) — Session 1 (V0 + regime analysis) ready to start.**
The iter-structural-edge S1 owner gate RULED (its LEDGER.md final entry): G1 accepted (no
D5-surviving exit component — trend-breakout + ema-alignment refuted in dollars; R3's 8/8 and
v6a were the F70 artifact; no-TP value-destroying), early stop accepted (power: ~6.3k trades/arm
needed vs 100–900 available), D7 park ratified (mtf-trend, reversible), and
**`docs/iterations/iter-viability/PLAN.md` adopted as the successor program** (V0–V7, decisions
D1–D8: MDE line in every pre-registration, D5′ bootstrap gates, auto-tune doctrine, parallel
guards, 2024 era-holdout + EMBARGO-2).
**Session 1 mandate:** (a) **V0 — challenge-model truth**: verify FTMO current terms (Phase-1/2
time limits, Swing account, daily-loss definition/intraday/reset, scaling) against
`config/prop-firms/ftmo-standard.json`; correct config + `ChallengeSimulator`; add P(bust) and
E[time-to-target] as sv2 outputs; owner signs account type [gate GV0]. (b) **Regime-conditioning
analysis** (old S2(b), zero new runs): 2×2 family-class × census-half interaction over existing
census trades, external regime variables (realized-vol percentile + efficiency ratio), block
bootstrap on the interaction. Pre-register BOTH in `docs/iterations/iter-viability/LEDGER.md`
(with MDE lines per D1) before anything scored. **Session 2:** V1 Dukascopy 2019–24 bid/ask
backfill (importer + overlap-year validation). Findings continue at **F73**.
Background: the alpha-loop close had decided portfolio-of-cells gated on an OOS-honesty Phase 0;
the 2026-07-16 research session ran that gate's moral equivalent on recorded data (split-half
selection test, **F64**) and it FAILED — 38 H1-positive cells earned $116,518 in H1 and −$880 in
H2, 24% persistence (worse than coin flip), independently corroborated by R4's embargo result. Per
the close decision's own stop rule, the portfolio is demoted to a conditional final phase (S6).
Direction: hunt **rule-level structural edges** (exit layer first — F65 MFE-capture 0.42 + R3's
8/8 `runner-aggressive` are two independent lines at one lever), cells as instances, family-pooled
evaluation, D5-tightened anti-overfit, EMBARGO-2 = everything after 2026-07-05 (first touch at S5,
≥45 accrued days, 60d complete ~2026-09-04). Findings continue at F69 (F64–F68 pre-filed in
RESEARCH.md). Sessions run MANUALLY for now (owner call 2026-07-16): interactive Claude sessions
deliver stages one at a time; the conductor plan (`conductor-structural-edge.plan.json`, repo root)
stays committed and TRACKER.md stays in its parseable checkpoint format so the owner can hand the
remaining stages to conductor later. Follow the session protocol in PLAN.md §4 — QA the previous
session's claims against artifacts before building.
**Read first:** `docs/iterations/iter-viability/TRACKER.md` (Handoff block) →
`docs/iterations/iter-viability/PLAN.md` (V0–V7, decisions D1–D8, owner-asks map §6) →
`docs/QUANT-REVIEW-RESPONSE-2026-07.md` (the rationale: power math, FTMO reframing, doctrine) →
`docs/iterations/iter-structural-edge/LEDGER.md` (tail: S1 close + owner-gate ruling) →
`docs/iterations/iter-structural-edge/RESEARCH.md` (F64–F68) →
`docs/iterations/iter-alpha-loop/HANDOVER.md` (what the machine already proved).
**Tracker:** `docs/iterations/iter-viability/TRACKER.md`
**Branch:** `iter/viability` (from `main` at the S1-gate merge; merge back to `main` at owner gates)
**Gate baseline (re-verified live at S0 close, 2026-07-16):** build 0err/5warn · Unit 767/0/6 ·
Integration 153/0/0 · Sim-fast 144/0/0. (S0 added 6 tests: sv2 survival pins + F64 machinery.)
**Live parity:** **EURUSD `VERDICT: PASS`** (tape `a89d37b5` / ctrader `e497806d`) — TradeCount exact ·
EntryPrice **0.0 ticks** · Lots exact · ExitPrice **100% within, 0.0 ticks** · Commission 0.53% ·
Swap 0.44% · NetPnL 0.45%. **Tolerance budget UNTOUCHED.** XAUUSD (14 trades) green on everything
except NetPnL (**F48**, still open — see bugfix queue in R5-AUDIT.md §3). Every trade matches cTrader
byte-for-byte on entry, exit, stop, lots, timestamps.

**What shipped after P4 (summarized — R5-AUDIT.md has the audited detail):** X0-X5 (run queue,
progress truth, Runs page rework, trade chart rework, data-manager auto-sync, god-class refactor —
all live-verified), R1' (the valid 252-cell baseline census, D13-conformant), R3 (2 refinement
sessions, 24 pre-registered variants, walk-forward + OOS-ratio cull, 2 cells parked on real
evidence), R4 (FTMO dress rehearsal on the embargoed window — **headline: all 4 full-year survivors
stalled or went net-negative on the one unseen 60-day window, a return-velocity failure, not a risk
failure** — full numbers in `evidence/candidate-cards.md`), R5 (this audit).

**What shipped (P4):** three defects, all found by making the venue TELL us rather than inferring.
**F43** resting orders do NOT fill at their own price — cTrader replays M1 as four synthetic O/H/L/C
ticks, so an order fills on the first tick to BREACH its level (stops fill THROUGH, limits fill BETTER);
the short-exit spread was also counted TWICE. **F44** venue symbol specs were captured in memory and
never persisted (this was the already-filed F25), so the tape — which never meets a cBot — priced off
fabricated symbols.json. **F45** swap read as money (it's PIPS — the already-filed F28), negated (it's
already signed), and weekends charged (they aren't). **F46** closing commission billed at the entry price.
The previous session's "fill at the bar close" stop model was a number-fitting fudge and is REVERTED.

**⚠ The fill and swap models are pinned against RECORDED VENUE OUTPUT** (`VenueFillModelTests` — six real
cTrader fills; `VenueSwapModelTests` — three real swap charges). Every one of these bugs had been guarded
by a GREEN test that asserted the *assumption* instead of the venue ("a limit fills at exactly the named
price, never a better one"). **A test written from the same reasoning as the code cannot falsify that
reasoning.** Do not "simplify" those two files.

**Still true, and load-bearing:** any phase touching `CTraderBrokerAdapter`, `TradingEngineCBot.cs`,
`SymbolInfoRegistry`, order-entry/expiry, or the cost/spread model **MUST run a live compare-both before
being called done** — not just the credential-free gate battery. Capturing a venue spec for a new symbol
requires ONE cTrader run on it; the tape then prices off the broker on every later run.

**Owner decisions (2026-07-12):** (a) **F47 — cTrader prices backtest commission at ONE reference spot**
(constant -20.67 EUR/lot across an 18% gold move): **ACCEPTED as the venue's artifact, deliberately NOT
matched** — reproducing it would make a run's costs depend on when it ran. The gate exempts it only when
the venue's own data proves the artifact (≥4 trades, per-lot charge flat <2% while prices moved >5%).
(b) **M1 tick-synthesis realism bias: PARKED.** Limits/TPs fill BETTER than their level (an XAUUSD TP
filled 27 pts through target). Parity is honest — both legs share the model — but the VENUE is not
modelling reality. **X0's absolute PnL inherits this optimistic bias; relative strategy ranking is
unaffected.** Revisit with tick data. PARITY-TRUTH-4 §5.

**Known open (not blocking X0):** **F48** — the last parity divergence: XAUUSD gross differs 1.37% though
prices and lots are IDENTICAL, so only the pip's *worth* differs. `PipCalculator.PipValuePerLot` uses the
time-varying `getCrossRate("USD","EUR")` for XAUUSD vs the price-accurate `rawPipValue / currentPrice` for
EURUSD; the per-trade ratio DRIFTS ⇒ a rate-*timing* issue, invisible on a USD account. Also F26
(PreTradeGate ignores CommissionType), F29 (reconcile matcher's 5-min window), F36/BTCUSD `TRADES_LOST`
(cTrader-leg trade capture still lossy — fix before BTCUSD parity means anything). The `ctrader-e2e`
`CtraderE2EHarnessSmokeTests` fail with 0 trades — PRE-EXISTING environmental cTrader CLI bug, not a
regression; re-confirm before spending time on it.

**Next:** **X0 — start the alpha loop.** Parity is locked; the M1 bias above is documented, not a blocker.



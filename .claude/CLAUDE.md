# CLAUDE.md — Zeus

## What This Is

Zeus is a **position management system** that uses weather forecasts as one input. It is NOT a signal engine that happens to trade. The system's value is in holding and exiting correctly, not in finding edges — every bot finds edges with the same public data.

## Core Design Principle: Trade-Centric Architecture

Every module exists to serve the lifecycle of a trade. A trade is born (discovery), held (monitoring), and dies (settlement or exit). The Position object must carry its full identity — direction, probability space, entry method, decision-time data snapshot, exit strategy — through every module it touches. When modules pass bare floats instead of typed Position context, interface bugs appear: probability spaces get double-flipped, time context gets lost, processing state isn't tracked.

**The 10 P0 bugs from code review were ALL interface bugs, not logic bugs.** Each module's internal math was correct. But when module A's output passed to module B, semantic context was lost. This is exactly how Rainstorm died.

## System Phase: OPERATING (not building)

Zeus is past the building phase. Paper trading shows $244 profit. The codebase has 231+ tests, 59 source files, and a running daemon. **Every change from this point is a change to a live system with real state, real positions, and real money at stake.**

In building phase, the question is "does it work?" In operating phase, the question is "what happens when it breaks at 3am and nobody is watching?"

### Structural Decisions, Not Mechanism Counting

When facing a new risk category (e.g., "paper→live needs isolation"), do NOT enumerate individual failure modes and patch each one. That's打地鼠 (whack-a-mole). Instead:

1. **Identify the structural decision** — what one design choice, if made correctly, makes an entire category of failure impossible?
2. **Trace the decision through all surfaces** — a structural decision has N consequences on N different modules. List them all. They are not "N mechanisms" — they are one decision expressed N times.
3. **Implement the decision once, at the lowest level** — e.g., `state_path()` in config.py covers 5 files with one function. Not 5 separate path changes.
4. **Verify the decision covers the future** — 1 month, 3 months, 1 year. If the decision blocks a plausible future (multi-platform, backtest mode, parallel paper+live), it's the wrong decision.

Example: The prompt said "Zeus has 7/22 of Rainstorm's chain-safety mechanisms, missing 15." This framing suggests 15 separate patches needed. The structural analysis showed: 22 mechanisms = 5 structural decisions. Implementing 5 decisions covered all 22.

### The 5 Structural Decisions (Live Safety)

| # | Decision | What it covers | Single point of control |
|---|----------|---------------|------------------------|
| 1 | **Exit = Order Lifecycle** | Sell order, retry/backoff, collateral, rounding, crash recovery | `exit_lifecycle.py` |
| 2 | **Chain Truth with Uncertainty** | Reconciliation, immutable snapshot, quarantine, ignored tokens, incomplete API | `chain_reconciliation.py` |
| 3 | **Entry = Pending State** | Fill verification, pending_tracked lifecycle, post-trade refresh | `fill_tracker.py` |
| 4 | **Provenance** | Paper/live isolation, env tagging, contamination guard, state path isolation | `config.state_path()` + `Position.env` |
| 5 | **Single-threaded per Mode** | Cycle overlap prevention | `main.py` cycle lock |

When a new live-mode risk is discovered, first ask: "Which structural decision does this belong to?" If it doesn't belong to any of the 5, it might be a new structural decision — or it might be a symptom of an incomplete existing one.

### Provenance Model (State Architecture Foundation)

Zeus's state has two orthogonal dimensions: **content type** and **provenance**.

**Content types and their isolation:**
- **World data** (ENS, observations, settlements, calibration) → shared `zeus.db`, no mode tagging. Paper's calibration pairs feed live's Platt refit — they come from real settlements.
- **Decision data** (trade_decisions, chronicle, decision_log) → shared `zeus.db` with `env` column. Paper and live decisions in same DB enables cross-env comparison.
- **Process state** (positions, strategy_tracker, status_summary, control_plane, risk_state) → physically isolated via `state_path()`. Paper and live daemons cannot read each other's state.

**`state_path()` is the single control point.** All per-process files must use it. zeus.db does not (shared world data). If this invariant is violated, contamination becomes possible.

## Core Debug Principle

**Code shows function. Code NEVER shows logic.** When facing bugs:
- A list of 10 bugs is usually 10 symptoms of 1-2 design failures
- Patching individual bugs creates more bugs (the fix breaks assumptions other modules rely on)
- Before fixing ANY bug: understand WHY the code was written this way, trace the fix through ALL callers and dependents
- Ask first: "Does Rainstorm have a design that makes this entire CATEGORY of bug impossible?" If yes, port the design. Only then fix individuals.
- "看一步想十步" — every fix must consider 10 steps of downstream consequences

### Operating-Phase Debug Protocol

In building phase, bugs are in YOUR code. In operating phase, bugs are in the INTERACTION between your code, the chain, the API, time, and concurrent state.

When something goes wrong in production:
1. **Don't fix the symptom.** A position stuck in `sell_pending` is not "fix sell_pending." It's "why did the exit lifecycle state machine not transition?"
2. **Check which structural decision is incomplete.** Every live failure maps to one of the 5 decisions. If it doesn't, you found a 6th.
3. **The fix must be a property of the decision, not a patch on the symptom.** Adding `if exit_state == "sell_pending" and stuck_for > 1h: force_close()` is a patch. Making `check_pending_exits()` handle all non-terminal states is a structural fix.
4. **Verify the fix covers unknown variants.** If CLOB returns a new status string tomorrow that you've never seen, does the state machine handle it? If not, the fix is incomplete.

## Design Authority

**Read these BEFORE writing any code. Every design decision must trace to one of them.**

| Document | Location | Domain |
|----------|----------|--------|
| Quantitative Research | `~/.openclaw/project level docs/rainstorm_quantitative_research.md` | Calibration math, Kelly, sample sizes, overfitting |
| Architecture Blueprint | `~/.openclaw/project level docs/rainstorm_architecture_blueprint.md` | Risk guard, cost layering, failure modes |
| Market Microstructure | `~/.openclaw/project level docs/rainstorm_market_microstructure.md` | Edge thesis, participant types, entry timing |
| Statistical Methodology | `~/.openclaw/project level docs/rainstorm_statistical_methodology.md` | Three σ, instrument noise, FDR, data versioning |
| **Zeus Spec** | `~/.openclaw/project level docs/ZEUS_SPEC.md` | Complete system specification |
| 5. First Principles | `~/.openclaw/project level docs/zeus_first_principles_rethink.md` | Why position management > signal precision. Why type safety is architecture. |
| **6. Blueprint v2** | **`~/.openclaw/project level docs/zeus_blueprint_v2.md`** | **THE architectural authority. Position-centric design. CycleRunner, Decision Chain, Truth Hierarchy, Exit = Entry rigor. Supersedes ALL prior architecture docs including the original spec's architecture sections.** |

**Document 6 (Blueprint v2) is the architectural authority.** It supersedes the original spec's module layout, data flow, and lifecycle design. Documents 1-4 remain valid for their specific domains (math, risk thresholds, market microstructure, statistics). Document 5 is the reasoning that led to Document 6. If any code contradicts Document 6, STOP and restructure.

---

## Types

### Temperature
All temperatures are `float` internally, in the city's settlement unit.
- US cities: °F (float)
- European cities / Asian cities: °C (float)
- **ANY function with a temperature-space threshold** (spread, std, divergence, instrument noise) **MUST accept a `unit` parameter.** Hardcoded °F thresholds applied to °C values is a CATEGORY of bug — Rainstorm lost real money to this (9 positions). Only probability-space thresholds (0-1) are safe to hardcode.
- Instrument noise: σ = 0.5°F for US, 0.28°C for °C cities (Statistical Methodology §1.2).
- NEVER: bare `int`. Rounding to integer happens ONLY in `EnsembleSignal.p_raw_vector()` during WU settlement simulation.

### Probability
- `p_raw`: `np.ndarray`, shape `(n_bins,)`, sums to 1.0. Unnormalized is a bug.
- `p_cal`: `np.ndarray`, shape `(n_bins,)`, sums to 1.0 AFTER normalization.
- `p_market`: `np.ndarray`, shape `(n_bins,)`. Sum is the vig (typically 0.95-1.05).
- `p_posterior`: `np.ndarray`, shape `(n_bins,)`, sums to 1.0.
- All probabilities are `float` in [0.0, 1.0]. Values outside this range are bugs.

### Money
- All USD amounts are `float`. No cents rounding until display.
- `entry_price`: cost per share, [0.01, 0.99].
- `size_usd`: total dollar amount of order.
- `pnl`: signed float. Positive = profit.

### Time
- All timestamps are UTC `datetime` objects internally.
- Convert to local time ONLY for Wunderground day boundary calculation.
- Use `zoneinfo.ZoneInfo`, not `pytz`.

---

## Module Interfaces (quick reference — do NOT re-read source files for this)

```
EnsembleSignal(members_hourly, city, target_date)
  .p_raw_vector(bins, n_mc=5000) → np.ndarray (n_bins,)
  .spread() → float
  .is_bimodal() → bool
  .boundary_sensitivity(boundary) → float
  .member_maxes → np.ndarray (51,)

ExtendedPlattCalibrator()
  .fit(p_raw, lead_days, outcomes, n_bootstrap=200)
  .predict(p_raw, lead_days) → float
  .bootstrap_params → list[tuple[float, float, float]]  # (A, B, C)
  .n_samples → int

calibrate_and_normalize(p_raw_vector, calibrator, lead_days) → np.ndarray

compute_alpha(calibration_level, ensemble_spread, model_agreement,
              lead_days, hours_since_open) → float

MarketAnalysis(ens, bins, calibrator, alpha)
  .find_edges(n_bootstrap=500) → list[BinEdge]
  .p_raw, .p_cal, .p_market, .p_posterior → np.ndarray
  .vig → float

kelly_size(p_posterior, entry_price, bankroll, kelly_mult) → float

vwmp(best_bid, best_ask, bid_size, ask_size) → float
```

---

## Calibration Levels

| Level | Condition | Platt Regularization | Edge Threshold × | α |
|-------|-----------|---------------------|-------------------|-----|
| 1 | n ≥ 150 | Standard (C=1.0) | 1× | 0.65 |
| 2 | 50 ≤ n < 150 | Standard (C=1.0) | 1.5× | 0.55 |
| 3 | 15 ≤ n < 50 | Strong (C=0.1) | 2× | 0.40 |
| 4 | n < 15 | No Platt (P_raw) | 3× | 0.25 |

---

## Attribution Fields (MANDATORY on every trade_decision)

```sql
edge_source TEXT,         -- 'favorite_longshot' | 'opening_inertia' | 'boundary' | 'vig_exploit' | 'mixed'
bin_type TEXT,             -- 'shoulder_low' | 'shoulder_high' | 'center' | 'adjacent_boundary'
discovery_mode TEXT,       -- 'opening_hunt' | 'update_reaction' | 'day0_capture'
market_hours_open REAL,    -- hours since market opened when entry placed
fill_quality REAL,         -- (execution_price - vwmp) / vwmp — positive = worse than expected
```

These are NOT optional metadata. They are the only way to know WHY the system makes or loses money. The harvester aggregates P&L by these dimensions weekly to answer:
- Which edge source is actually profitable?
- Which direction (buy_yes vs buy_no) contributes more?
- Is Opening Hunt better than Update Reaction?
- Which cities are losing money?

---

## Failure Taxonomy

Every system anomaly maps to exactly one failure type with a pre-defined response:

| Failure Type | Trigger | Response |
|-------------|---------|----------|
| `DATA_STALE` | ENS data > 6h old | YELLOW: skip new entries this cycle |
| `DATA_CORRUPT` | Members ≠ 51 or temp outside physical range | Skip market entirely |
| `MODEL_DRIFT` | Hosmer-Lemeshow χ² > 7.81 on last 50 pairs | YELLOW + force Platt refit |
| `MARKET_STRUCTURE` | Vig > 1.08 or < 0.92 sustained | Flag for vig arbitrage or skip |
| `EXECUTION_DECAY` | Fill rate < 30% for 7 consecutive days | Alert: adjust limit offset |
| `EDGE_COMPRESSION` | Same edge type's avg magnitude shrinks 50% over 30 days | Alert: this edge may be dying |
| `REGIME_CHANGE` | ENSO state transition or SSW detected | YELLOW: raise edge threshold 2× |
| `COMPETITION` | Shoulder bin avg overpricing ratio drops from 3× to < 1.5× | Alert: market efficiency increasing |

RiskGuard checks for these. Each maps to GREEN/YELLOW/ORANGE/RED per spec §7.3.

---

## Rainstorm Autopsy: Lessons for Zeus

### Lesson 1: Position Lifecycle Must Be Airtight

CHURN_DUPLICATE + orphan positions = -$93.63（55% of all trades）。
引擎每 120 秒重复买入已持有的仓位，然后以 spread loss 卖出。

Zeus 的状态机在架构上防止了重入。但更深的教训是：
portfolio ↔ chain 之间任何不一致（orphan: portfolio 有但 chain 没有；
phantom: chain 有但 portfolio 没有）都是静默的资本泄漏。
追踪 `portfolio_chain_mismatches` 作为系统健康指标。> 0 就是有东西坏了。

### Lesson 2: 对市场保持敬畏 — 入场和退出都要有罪推定

模型正确 22 次（+$32.20），错误 54 次（-$169.36）。
模型最自信时（avg edge 0.317）恰恰是它最错的时候。

**把每一个 "edge" 当作有罪推定，直到数据证明它无罪。**

但更深的版本是：**退出决策也要有罪推定。** Zeus 的 false
EDGE_REVERSAL 不是"发现不存在的 edge"——是"制造不存在的退出理由"。
入场经过 Platt + Bootstrap CI + FDR + Kelly 四层验证，退出只经过
"刷新 ENS 看方向" 一层检查。这个不对称是最大的风险源。

**不确定时的默认行为：HOLD to settlement。** 入场决策已经被验证过了；
退出决策必须达到同等严格度才能推翻入场决策。

Phase 0 通过是一个好消息——结构性 mispricing 确认存在。但这不意味着
可以放松。Alpha 衰减是必然的：更多的 bot 进入、做市商覆盖改善、
散户学习、平台规则变更。今天 3× 的 shoulder overpricing 可能明年变成
1.5×，后年变成 1.1×。

Zeus 必须持续回答的问题不是"我今天赚了多少"，而是：
- edge_source 维度上，每种 edge 的平均大小在过去 30/60/90 天的趋势是什么？
- EDGE_COMPRESSION failure type 是否触发过？
- 如果所有结构性 edge 缩小到无法覆盖执行成本，系统是否能自动停止交易？

当 alpha 衰减到零时，正确的行为不是试图找新的 alpha——
而是停止交易、保住资本、等待新的市场结构出现。
RiskGuard 的 EDGE_COMPRESSION 检测就是为这个时刻设计的。

### Lesson 3: Execution Asymmetry Kills

模型正确时平均赚 $1.46，错误时平均亏 $3.14。在二元市场中这不应该
发生。原因是没有 VWMP、赢家退出太早、输家持仓太久。

Zeus 用 VWMP 定价、hold-to-settlement、EDGE_REVERSAL 作为唯一
信息驱动退出。但要监控 fill_quality——如果系统性为正（执行价持续
差于 VWMP），limit offset 需要调整。

---

## Critical Rules

### Data Integrity (ABSOLUTE)
- **NEVER fabricate, synthesize, or generate fake data.**
- **NEVER use data without `available_at <= decision_time` constraint.**
- **Four timestamps mandatory** on every forecast: `issue_time`, `valid_time`, `available_at`, `fetch_time`.
- **Settlement truth = Polymarket settlement result.**

### Statistical Discipline
- **Three σ are distinct:** σ_ensemble, σ_parameter, σ_instrument. All three flow into double bootstrap CI.
- **FDR control:** p-values from `np.mean(edges <= 0)`, NEVER approximated.
- **No per-position stop loss.** Only EDGE_REVERSAL triggers exit.
- **24 calibration buckets** (cluster × season). Lead time is Platt input feature, NOT bucket dimension.

### Execution
- **Limit orders ONLY.** Timeout varies by mode: Opening Hunt 4h, Update Reaction 1h, Day0 15min.
- **VWMP** for all edge calculations. Never mid-price.
- **Whale toxicity detection:** Cancel orders on adjacent bin sweeps.

### Architecture
- Standalone Python daemon (launchd). NOT OpenClaw multi-agent.
- RiskGuard is separate process with own SQLite DB (mode-isolated via `state_path()`).
- Single config file. No `.get(key, FALLBACK)` pattern.
- Paper/live state isolation via `config.state_path()` — one function, all per-process files.
- `zeus.db` shared between modes (world data + env-tagged decisions).
- Exit lifecycle: `exit_lifecycle.py` (sell order state machine, not `close_position()` direct).
- Entry lifecycle: `fill_tracker.py` (pending_tracked → entered/voided).
- Collateral check: `collateral.py` (fail-closed before every sell).
- Cycle overlap: `threading.Lock` in `main.py` (no concurrent cycles).

---

## Error Handling

### API Failures
- Open-Meteo: retry 3× with 10s backoff. If failing, skip market this cycle. Do NOT use stale ENS.
- Polymarket CLOB: retry 2× with 5s backoff. If failing, cancel pending orders and wait.
- Wunderground: retry 3×. If failing, flag Day0 as unavailable.

### Data Validation
- ENS response < 51 members: **reject entirely**. Do not pad.
- P_raw vector sum ≠ 1.0 (±0.001): normalize + log warning.
- VWMP with total size = 0: fall back to mid-price + log.
- Platt predict() output outside [0.001, 0.999]: clamp + log.

### Never Silently Fail
Every function that can fail must either raise an exception or return `Optional[T]`. NEVER `return 0.0` on error. This is how Rainstorm died.

---

## Continuous Self-Review Protocol

**After completing EVERY .py file, you MUST run a Sonnet subagent to review it.** This is not optional. Do not skip this step even if you are confident the code is correct.

### The Review Cycle

```
WRITE code → WRITE test → RUN test (Sonnet subagent) → REVIEW code (Sonnet subagent) → FIX issues → NEXT file
```

### Review Subagent Template

After writing each file, spawn a Sonnet subagent with this exact prompt pattern:

```
Review zeus/src/{module}.py against the following checklist. Return PASS or FAIL for each item with a one-line explanation. Do NOT suggest style improvements — only flag correctness and contract violations.

Checklist:
1. TYPES: Do all function signatures match the interfaces in CLAUDE.md "Module Interfaces"?
2. UNITS: Is temperature handling unit-safe? Any bare int where float is required? Any °F/°C mixing?
3. FALLBACKS: Are there any `.get(key, HARDCODED_DEFAULT)` patterns? (forbidden)
4. SILENT FAIL: Are there any bare `except: pass` or `return 0.0` on error? (forbidden)
5. TIMESTAMPS: Do all DB writes include all 4 timestamps? (issue_time, valid_time, available_at, fetch_time)
6. NORMALIZATION: After any Platt calibration, is the probability vector re-normalized to sum=1.0?
7. P_VALUE: Is any p-value computed via approximation formula instead of np.mean(edges <= 0)? (forbidden)
8. IMPORTS: Are there any imports from rainstorm/ or references to v1 code? (forbidden)
9. FILE SIZE: Is the file > 250 lines (excluding comments/blanks)? If so, suggest a split point.
10. SPEC TRACE: Can each major function be traced to a specific spec section? List the mapping.
```

### When Review Finds Issues

- **FAIL on items 1-8:** Fix immediately before moving to next file.
- **FAIL on item 9:** Split the file, then re-review both halves.
- **FAIL on item 10:** Add a `# Spec §X.Y` comment to the function.

### Weekly Full-Codebase Review

At the end of each week (or every 3 sessions), run a comprehensive review:

```
Spawn Sonnet subagent:
"Read every .py file in zeus/src/. For each file, check:
1. Does it have a corresponding test file in tests/?
2. Are all functions used? (grep for each function name across the codebase)
3. Are there any circular imports?
4. Are there any TODO comments older than 1 session?
Report: list of files with issues."
```

---

## Testing Contract

Every `.py` file in `src/` MUST have a corresponding `test_*.py` in `tests/`.

### What Tests Must Cover
1. Happy path
2. The specific edge case listed in `ZEUS_IMPLEMENTATION_PLAN.md §4.2`
3. Failure mode (None, empty, out of range inputs)

### What Tests Must NOT Do
- No network calls (mock all API clients)
- No file system writes outside `/tmp`
- No sleeping or timing-dependent assertions
- No randomness without seed (`np.random.seed(42)`)

### Test Running
Always use a Sonnet subagent to run tests:
```
Spawn Sonnet subagent: "cd zeus && source .venv/bin/activate && python -m pytest tests/test_X.py -v"
```
Do NOT run tests in the main context — save context for decision-making.

---

## Debugging Protocol

1. Test fails → read the FULL error traceback (don't guess)
2. Numeric precision issue: use `pytest.approx()` with tolerance
3. Random seed issue: ALWAYS `np.random.seed(42)` in test setup
4. Do NOT fix a test by weakening the assertion. Fix the CODE or fix the expectation with documented reasoning.
5. Maximum 3 debug attempts per test. After 3 fails, document in `ZEUS_PROGRESS.md` and move on.

---

## Discovery Protocol

If you discover something that contradicts the spec:
1. **STOP implementing.** Do not work around the issue.
2. Document the discovery in `ZEUS_PROGRESS.md` with exact details.
3. Tag it as `[BLOCKING]` or `[NON-BLOCKING]`.
4. `[BLOCKING]`: stop the session, ask Fitz for guidance.
5. `[NON-BLOCKING]`: document it, continue, flag for review.

---

## Session Handoff

### At Session End (MANDATORY)
1. Run Sonnet subagent: `pytest tests/ -v` — all must pass
2. `git add` specific files + `git commit -m "Session N: [summary]"`
3. Update `ZEUS_PROGRESS.md` with completed/in-progress/next tasks
4. If a module is half-written, leave `# TODO(session_N+1): [what's left]` at the exact stop point

### At Session Start (MANDATORY)
1. Read `ZEUS_PROGRESS.md` (< 200 lines)
2. Read this `CLAUDE.md`
3. Run Sonnet subagent: `pytest tests/ -v` to verify baseline
4. Read ONLY the spec sections relevant to today's task (use offset/limit)
5. Do NOT re-read the four research documents

---

## File Size Limit

No single `.py` file should exceed 250 lines (excluding comments and blanks). If approaching this limit, split by responsibility. Known split candidates:

```
market_analysis.py → market_analysis.py (class + edge scan) + bootstrap.py (double bootstrap logic)
riskguard.py → riskguard.py (main loop) + metrics.py (Brier, H-L, etc.)
```

---

## Subagent Rules

- Subagents do mechanical tasks ONLY (scan, verify, run commands, review)
- Subagent output ALWAYS requires main agent review before acting on it
- If subagent returns > 50 lines of code, extract interface + key logic only — main agent writes implementation
- Use `model: "sonnet"` for scanning/review/testing. Use `model: "opus"` for math verification only.

---

## What NOT To Do

- Do NOT reference Rainstorm v1 code for design decisions
- Do NOT use Gaussian CDF for probability estimation — not for live signals AND not for Platt training data. Rainstorm's forecast_log (mean+std) is used for TIGGE backfill prioritization only, never as approximate P_raw
- Do NOT create 72 calibration buckets
- Do NOT implement per-position stop loss
- Do NOT use mid-price for edge calculations
- Do NOT use KL divergence for model agreement
- Do NOT trust any "statistical finding" from Rainstorm v1
- Do NOT skip the Sonnet self-review after writing a file
- Do NOT read research documents during implementation sessions
- Do NOT run tests in the main context (use Sonnet subagent)

---

## Rainstorm Code Reuse Rules (Updated)

The original rule "NO code from Rainstorm" was correct at launch — Zeus needed a clean break from a system with contaminated data and broken signal math. But Zeus is now independently hitting the same walls Rainstorm hit. Refusing to inherit battle-tested solutions is wasting time rediscovering old lessons.

**What to reuse from Rainstorm (copy directly or copy design):**
- **Value types** (Temperature, TemperatureDelta): copy verbatim. Math infrastructure, not business logic.
- **Position lifecycle** (8-layer anti-churn, void_position, administrative exits, buy_no independent exit): copy design, adapt to Zeus data structures.
- **Chain reconciliation** (chain-first, ghost detection, orphan quarantine): copy. Live prerequisite.
- **Day0 observation math** (observation_confidence, diurnal model, divergence guard): copy. 14 months of IEM ASOS calibration.
- **Execution patterns** (edge recheck, sell-side price, stale cleanup, orphan handling): copy design.

**What NOT to reuse:**
- **Signal generation** (ensemble weights, forecast combination, edge calculation): Zeus has its own math (ENS member counting, not Gaussian CDF).
- **Calibration parameters** (error_db values, Platt coefficients, std estimates): contaminated by v1's inverted bias formula.
- **Config values** (thresholds, edge minimums, Kelly fractions): Zeus has its own tuning.

**The test:** Does this code's correctness depend on Rainstorm's signal chain being correct? If NO → safe to reuse. TemperatureDelta.__truediv__ returning a z-score is mathematically correct regardless of what Platt model produced the inputs. void_position(pnl=0) is correct regardless of entry signal quality.

## Inherited Data

Data in `~/.openclaw/workspace-venus/rainstorm/state/rainstorm.db`. Import via `scripts/migrate_rainstorm_data.py`.

Key: `settlements` (1,634), `observations` (227K+), `market_events` (14.9K), `token_price_log` (285K).

Data agent continuously running: WU 3,009+ city-days across 19 cities backfilling to 2024-06, TIGGE ENS archive downloading.

## Rainstorm Data Assets (READ-ONLY, do NOT migrate until agent stabilizes)

Data lives in rainstorm.db (2.4 GB). Each asset has a specific Zeus integration point — see spec §12.4 for the full table. Key items:

- **TIGGE** (separate dir, `51 source data/`): True 51-member ENS history → Platt training for DJF/JJA/SON. THE priority.
- **token_price_log** (319K): Market price trajectories → validate Opening Hunt timing parameters during paper trading.
- **WU** (3,009 city-days): Settlement precision audit (WU value vs Polymarket winning bin consistency) can run NOW.
- **forecasts** (171K, 5 models): Dynamic α calibration per city/season/model.
- **observations** (238K): Temperature persistence model — reality check when ENS predicts anomalous changes.
- **ladder backfill** (53,600): ENS bias correction (× 0.7) + forecast bust frequency analysis.
- **forecast_log** (333K): TIGGE download prioritization index (NOT for Gaussian P_raw training).
- **calibration_records.jsonl** (295 MB): Needs format inspection. May contain usable forecast-actual pairs.

## ENS Data Sources (Two Channels)

**Channel 1: ECMWF Open Data (Zeus's job — daily collection)**
- Rolling 2-3 day window. Data disappears after ~3 days. Missing a day = data lost forever.
- Zeus collects this via scheduled job, twice daily (after 00z and 12z).
- 51 members (50 perturbed + 1 control), parameter `2t`, steps 24-168h.
- Lower latency than Open-Meteo (source vs wrapper). Feeds Mode B (update reaction).
- Stored in `zeus.db:ensemble_snapshots`.

**Channel 2: TIGGE Archive (Data agent's job — historical backfill)**
- Permanent archive of historical ECMWF ENS. Goes back to 2006.
- Data agent downloads to `~/.openclaw/workspace-venus/51 source data/raw/tigge_ecmwf_ens/`.
- Zeus consumes via `scripts/etl_tigge_ens.py` (future session) when non-MAM data arrives.
- Currently 126 city-date vectors across 34 cities, ALL MAM. DJF/JJA/SON = 0.

**Channel 3: Open-Meteo Ensemble API (current primary, may be replaced)**
- 93-day rolling window. Free, no key. 51 ECMWF members via third-party wrapper.
- 1-3h additional latency vs ECMWF Open Data direct.
- Currently the only ENS source Zeus uses in production. May be demoted to fallback once ECMWF Open Data collection is stable.

## Commands

```bash
cd ~/.openclaw/workspace-venus/zeus && source .venv/bin/activate
ZEUS_MODE=paper python -m src.main       # paper trading
ZEUS_MODE=live python -m src.main        # live trading
python -m src.riskguard.riskguard        # risk guard (separate)
python -m pytest tests/                  # all tests
python scripts/baseline_experiment.py    # Phase 0 GO/NO-GO
python scripts/migrate_rainstorm_data.py # import data
python scripts/backfill_ens.py           # ENS P_raw backfill
```

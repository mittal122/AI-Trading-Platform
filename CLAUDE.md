# AI Trading Platform — Build Guide

This file is the single source of truth for building this project.
Read this before touching any code.

---

## Project Goal

Enterprise-grade algorithmic trading platform with AI integration.
Multi-asset. Multi-strategy. Eventually SaaS.
Current completion: ~45%.

---

## Stack

- Python 3.12 + FastAPI + Pydantic v2
- PyTorch + CUDA — Kronos model (OHLCV forecasting)
- Binance — market data provider
- pandas / numpy
- DB / Auth / Frontend — NOT YET BUILT

---

## Architecture Rules — NEVER VIOLATE

1. Factory pattern everywhere — never instantiate services directly
2. Strict layer separation:
   - IndicatorService calculates indicators — nothing else does
   - Strategy layer generates signals — never executes trades
   - Trading Engine executes — never calculates indicators or generates signals
   - Portfolio tracks positions — never generates signals
   - Schemas hold data — no business logic inside schemas
3. No hardcoded thresholds — all values come from config or env vars
4. BaseClass + Simple/concrete implementation pattern
5. Every new module needs a test file in tests/
6. Black formatting, descriptive names, functions 10-40 lines, classes 300-500 lines max
7. Conventional commits: feat(strategy): ..., fix(backtest): ..., test(risk): ...

---

## Canonical Pipeline

```
Binance
  → MarketService
  → IndicatorService
  → MarketRegime          ← NEW (just built)
  → SignalScore
  → TradeDecision
  → TradingSignal
  → TradingEngine
  → TradeManager
  → ExecutionEngine
  → PortfolioEngine
  → TradeRecorder
  → BacktestReport / Live Trade
```

AI prediction path (separate):
```
MarketService → KronosService → PredictionService → POST /predict
```

---

## API Base URL

`http://localhost:8000/api/v1`

Endpoints (actual paths — verified against running server):
- GET  /market/history      — historical candles (response: {symbol, interval, candles:[{timestamp,open,high,low,close,volume,amount}]}). Optional `end_time` (unix ms) — returns `limit` candles ending at/before that timestamp instead of the most recent ones (backward pagination, e.g. chart scroll-left)
- GET  /market/live         — latest candle
- GET  /indicator           — all indicators (SINGULAR path; response: {symbol, interval, indicators:{...}})
- GET  /strategy            — StrategyResponse (signal string, no regime/quality)
- GET  /strategy/signal     — FULL TradingSignal (direction, regime, quality_score/grade, atr, explanation, eta_candles/eta_display)
- GET  /strategy/scan       — every registered strategy analyzed independently on one symbol/interval → list[TradingSignal]
- GET  /strategy/multi-timeframe — one strategy analyzed independently across multiple timeframes → list[TradingSignal]
- GET  /strategy/available  — {"strategies": [...]} — factory's key list, single source of truth
- GET  /portfolio/analytics — Sharpe/Sortino/Calmar/etc.
- GET  /trades/history      — persisted trade history (filter: symbol, strategy, mode, limit, offset)
- GET  /trades/backtest-history + POST /trades/backtest-record
- POST /paper/start, /paper/stop · GET /paper/status · WS /paper/ws (2s status stream)
- POST /paper/order — one-click manual paper trade from a signal (entry/SL/TP); auto-closes at SL or TP, persists to DB
- GET  /paper/orders — manual paper trader state (balance, open + closed orders)
      Frontend: "Place Paper Trade" button lives inside SignalCard → shows on Dashboard + Signals
- POST /trading/start, /trading/stop?emergency=true · GET /trading/status
- POST /ai/chat, /ai/analyze, /ai/select-strategy, /ai/validate-trade, /ai/review-risk, /ai/sentiment
- POST /prediction/predict  — Kronos OHLCV forecast

Frontend consumes these via Vite proxy (/api → localhost:8000, ws:true). Client: frontend/src/api/client.ts

---

## Phase Completion Status

### Phase 1 — Core Infrastructure ✅ DONE

- [x] MarketService (Binance)
- [x] IndicatorService (15+ indicators)
- [x] BaseStrategy + StrategyFactory
- [x] RSIStrategy
- [x] SignalScore (adaptive weighted, regime-aware)
- [x] TradeDecision
- [x] TradingEngine (single-position, simulated)
- [x] ExecutionEngine
- [x] PortfolioEngine
- [x] PositionEngine (fixed risk sizing)
- [x] RiskEngine (ATR stop/TP)
- [x] TradeManager
- [x] TradeRecorder
- [x] BacktestEngine (candle replay, equity curve, win rate)
- [x] Kronos AI prediction endpoint
- [x] FastAPI app (lifespan, routers, schemas)
- [x] 15+ test files

### Phase 2 — Professional Strategy System ✅ DONE

- [x] Task 1: Market Regime Detection
      File: backend/app/services/strategy/market_regime.py
      Detects: STRONG_BULL / WEAK_BULL / STRONG_BEAR / WEAK_BEAR / SIDEWAYS
      Volatility: HIGH / NORMAL / LOW using ATR% + BB Width%
      Integrated into RSIStrategy → SignalScore

- [x] Task 2: Adaptive Signal Weighting
      Replaced fixed (+25/+20/+15) with weighted percentages:
      Trend 30% | Regime 25% | Momentum 20% | Volatility 15% | Volume 10%

- [x] Task 3: Better Confidence Calculation
      Factors: score gap (agreement), regime multiplier, volatility dampener

- [x] Task 4: Better Entry Filters
      File: backend/app/services/strategy/entry_filter.py
      BUY: bull trend (critical) + ADX (critical) + MACD + VWAP + RSI
      SELL: bear trend (critical) + ADX (critical) + MACD + VWAP + RSI
      Wired into RSIStrategy.generate_signal() — gates BUY/SELL decisions

- [x] Task 5: Advanced Exit Logic
      File: backend/app/services/trade/exit_manager.py + trade_manager.py
      Implemented: trailing stop, break-even, ATR reversal exit, time exit, signal reversal
      TradeState extended: peak_price, candles_held, atr_at_entry, trailing_stop_active

- [x] Task 6: Dynamic ATR Multiplier
      File: backend/app/services/risk/dynamic_atr.py
      Regime+volatility lookup table — 15 combinations
      Wired into RSIStrategy + all 4 new strategies

- [x] Task 7: Trade Quality Score
      File: backend/app/services/strategy/trade_quality.py
      0-100 score across: Trend(25) + Momentum(20) + Volume(20) + RR(20) + Regime(15)
      Grades: A+ / A / B / C / D / F
      Added quality_score + quality_grade to TradingSignal schema

- [x] Task 8: Strategy Explanation Engine
      File: backend/app/services/strategy/explainer.py
      Human-readable summary + market context + indicator snapshot + reasons + quality
      Added explanation field to TradingSignal schema

- [x] Task 9: Strategy Configuration
      File: backend/app/core/strategy_config.py
      All thresholds centralized: RSI, ADX, ATR multipliers, regime ADX, BB thresholds,
      entry filter confirmations, time exit, quality RR thresholds, supertrend params

- [x] Task 10: Multiple Strategies
      Files: ema_strategy.py, macd_strategy.py, breakout_strategy.py, supertrend_strategy.py,
      cta_trend_strategy.py, turtle_strategy.py, engulfing_scalp_strategy.py (all added 2026-07-02)
      All registered in StrategyFactory (keys: rsi, ema, macd, breakout, supertrend, cta_trend,
      turtle, engulfing_scalp)
      IndicatorService extended: previous_ema20/50, EMA crossover booleans,
      previous_histogram, MACD crossover booleans, supertrend + supertrend_direction,
      calculate_cta_trend() — 3 EMA-pair composite + 2 momentum sub-signals + realized vol,
      calculate_atr_at_period() — ATR at a caller-specified window (not fixed 14),
      rolling_channel() — highest-high/lowest-low over N closed candles,
      calculate_rsi_series() — full RSI series (not just latest scalar)

      CTA Trend (Systematic Trend Following, CTA-style): composite of 3 EMA-crossover pairs
      (10/50, 20/100, 50/200) + 2 time-series momentum sub-signals (90/180-bar lookback),
      averaged to [-1,+1]. Confidence = conviction (sub-signal agreement) + volatility-targeted
      exposure bonus. Stops/targets are ATR(20)-scaled (2.5x/4x), independent of the
      regime-based DynamicATR table other strategies use. All periods in strategy_config.py
      (CTA_* constants).

      Turtle Trading (Richard Dennis-style dual breakout): System 1 = 20-bar breakout,
      filtered by whether the LAST System-1 breakout in that direction was a loss (skip if it
      won, unless price also breaks the unfiltered 55-bar channel as a failsafe). System 2 =
      55-bar breakout, always taken, no filter. N = ATR(20), stops/targets are 2N/4N (fixed
      RR=2.0 by construction). The last-breakout-loss filter is a historical simulation
      (backward scan, capped at TURTLE_BACKWARD_SCAN_BARS=150) — kept in the strategy file,
      not IndicatorService, since it's a trade-outcome decision, not an indicator calc.
      Slowest strategy in the platform (~15s for a 500-candle backtest) due to this scan —
      acceptable but noticeably slower than the others. All periods in TURTLE_* config.

      Engulfing Scalp (long-only): price > EMA200 AND RSI14 > 50 AND a bullish engulfing
      candle on the last closed bar → BUY. Stop/target sized off the engulfing candle's own
      range (not ATR): stop = entry - 2x range, target = entry + (risk x RR 2.0) → fixed
      RR=2.0 by construction. Confidence gets a +10 bonus on bullish RSI divergence (price
      lower-low + RSI higher-low across the last 2 swing lows in a 20-bar window). All
      periods in ENGULF_* config.

      User-supplied 5 strategies total (Turtle, CTA Trend, EMA Pullback, SMC, Engulfing
      Scalp) across two conversations. Implemented: CTA Trend, Turtle, Engulfing Scalp (user
      explicitly requested each in turn). NOT implemented: EMA Pullback, SMC (Smart Money
      Concepts — most complex, has FVG/liquidity-sweep/HTF-structure logic) — user hasn't
      asked for these yet.

### Phase 3 — Advanced Risk Management

- [x] Kelly Criterion position sizing
      File: backend/app/services/position/kelly_position.py
      Formula: f = (bp - q) / b, where b=RR, p=win_rate, q=1-p
      Cap at 25% of equity

- [x] Trailing Stop implementation
      Move to exit_manager.py (Task 5 above — done there)

- [x] Drawdown protection
      File: backend/app/services/risk/drawdown_guard.py
      Track peak equity. If drawdown > 10%, halt new trades.
      If drawdown > 20%, close all positions.

- [x] Daily loss limit
      File: backend/app/services/risk/daily_loss_limit.py
      Track daily realized PnL. If daily loss > 2% of equity, halt trading for the day.

- [x] Partial exits
      In exit_manager.py: close 50% at 1:1 RR, let remaining run to full TP

- [x] Risk-adjusted position sizing
      In PortfolioEngine: cap single position at 5% of equity regardless of signal

### Phase 4 — Portfolio Analytics

- [x] Sharpe Ratio
- [x] Sortino Ratio
- [x] Calmar Ratio
- [x] Profit Factor
- [x] Maximum Drawdown
- [x] Win Rate, Avg Win, Avg Loss
- [x] Expectancy per trade
      File: backend/app/services/portfolio/analytics.py
      Add analytics endpoint: GET /api/v1/portfolio/analytics

### Phase 5 — AI Integration ✅ DONE (multi-model via NVIDIA NIM)

All 7 AI services route through a single NVIDIA NIM endpoint (one OpenAI-compatible
API, one NVIDIA_API_KEY) — NIM hosts each third-party model behind its own slug.
File: backend/app/core/ai_provider_config.py — connection + per-service ServiceModelConfig
File: backend/app/services/ai/llm_client.py — MultiProviderAIService (openai SDK, base_url=NIM)
NOT Anthropic/Claude — base_ai.py (old Anthropic-only base class) was removed.

| Service | File | Model (NIM slug) | Notes |
|---|---|---|---|
| Market Analyst | market_analyst.py | nvidia/nemotron-3-super-120b-a12b | thinking OFF (fast/credit-efficient) |
| Strategy Selector | strategy_selector.py | zai-org/glm-5.1 | best-guess slug — verify on build.nvidia.com |
| Trade Validator | trade_validator.py | deepseek-ai/deepseek-v4-pro | thinking ON (money-critical, highest reasoning) |
| Risk Manager | risk_manager.py | zai-org/glm-5.1 | |
| Sentiment Analyzer | sentiment_analyzer.py | minimaxai/minimax-m3 | multimodal-capable model, used text-only here |
| Chat Assistant | chat_assistant.py | moonshotai/kimi-k2.5 | best-guess slug |
| Backtest Explainer (NEW) | backtest_explainer.py | minimaxai/minimax-m2.7 | explains completed backtest metrics in plain English |

- [x] LLM Market Analyst — indicators+regime → sentiment + analysis + key levels
- [x] AI Strategy Selector — regime+performance → recommended strategy + reasoning
- [x] AI Trade Validator — APPROVE/REJECT + reason + risk_flags
- [x] AI Risk Manager — HOLD/REDUCE/CLOSE/TIGHTEN_STOP + suggested stop/size
- [x] News/Sentiment Analysis — headlines → BULLISH/BEARISH/NEUTRAL + score
- [x] AI Chat Assistant — POST /api/v1/ai/chat, multi-turn
- [x] Backtest Explainer — POST /api/v1/ai/explain-backtest — NEW, takes backtest
      metrics (win rate, Sharpe, etc.) → plain-English summary/strengths/weaknesses/suggestion
      Endpoints: /ai/analyze, /ai/select-strategy, /ai/validate-trade, /ai/review-risk,
      /ai/sentiment, /ai/chat, /ai/explain-backtest — all rate-limited via tier_rate_limit
      Model slugs + temperature/top_p/extra_body (thinking toggles) all in
      ai_provider_config.py, every value overridable via env var — no code change needed
      to fix a wrong slug.

### Phase 6 — Paper Trading ✅ DONE

- [x] Virtual account with live Binance prices (no real orders)
- [x] File: backend/app/services/paper/paper_trading_engine.py
- [x] Endpoint: POST /api/v1/paper/start, POST /api/v1/paper/stop, GET /api/v1/paper/status
- [x] Track virtual balance, virtual positions, virtual P&L
- [x] Real-time WebSocket price feed from Binance (kline stream via python-binance)
      PaperFactory.get_engine() → module-level singleton
      Uses all risk guards: DrawdownGuard, DailyLossLimit, 5% equity cap, partial exits
      VERIFIED LIVE (2026-07-02): started engine on 1m BTCUSDT, watched a real
      BUY → TAKE_PROFIT cycle execute end-to-end via backend log + DB row.
      NOT A BUG: the engine itself works correctly — it only trades when its
      strategy actually fires a signal on a closed candle (can look "silent"
      in choppy markets). Frontend gap (fixed): PaperTrade.tsx only showed the
      live in-memory engine's last 20 trades (reset on backend restart) and
      never showed ManualPaperTrader orders (from the SignalCard button) at
      all. Now also fetches GET /trades/history?mode=PAPER (durable, survives
      restarts, covers both auto-bot + manual trades) and GET /paper/orders.
      Engine itself is a server-side singleton — refreshing the browser was
      never actually stopping it; that's now visible in the UI too.

### Phase 7 — Live Trading ✅ DONE

- [x] Binance live order execution (market orders)
      File: backend/app/services/execution/binance_execution.py
      dry_run=True (default) simulates fills locally — no real orders
      dry_run=False places real market orders via Binance API

- [x] Add BINANCE_API_KEY, BINANCE_SECRET to .env (required for live mode)

- [x] Order confirmation + order tracking
      Every order logged to BinanceExecution._orders with order_id, fill price, fee, status

- [x] Emergency stop button endpoint: POST /api/v1/trading/stop?emergency=true
      Cancels all open Binance orders + market-sells open position immediately
      Sets emergency_stopped=True — engine requires app restart to re-enable

- [x] LiveTradingEngine: backend/app/services/trading/live_trading_engine.py
      Same WebSocket loop as PaperTradingEngine, routes execution through BinanceExecution
      Singleton via LiveTradingFactory

- [ ] Bybit adapter (future): bybit_execution.py

### Phase 8 — Database Integration ✅ DONE

- [x] PostgreSQL (production) + SQLite (default, zero-config dev/test)
      DATABASE_URL env var: not set → sqlite+aiosqlite:///./trading.db
                            set → use as-is (postgresql+asyncpg://...)

- [x] SQLAlchemy 2.0 async ORM — backend/app/db/
      database.py: engine, AsyncSessionLocal, Base, create_tables(), get_db()
      models.py: Trade, BacktestRun, Position, Portfolio, Strategy, User
      repository/trade_repo.py: save, get_history (filterable), count_by_mode
      repository/backtest_repo.py: save, get_recent (filterable)

- [x] Alembic migrations
      alembic.ini + alembic/env.py (async-compatible, render_as_batch for SQLite)
      alembic/versions/*_initial_schema.py — all 6 tables

- [x] DB persistence layer — backend/app/services/db_service.py
      DatabaseService: save_trade(), get_trade_history(), save_backtest_run(), get_backtest_history()

- [x] Tables auto-created on startup (main.py lifespan calls create_tables())

- [x] Trade history endpoints — GET /api/v1/trades/history
      Filters: symbol, strategy, mode (PAPER/LIVE/BACKTEST), limit, offset, pagination total
      GET /api/v1/trades/backtest-history — paginated (limit up to 1000, offset), returns
      total + full detail analytics per run (winning/losing trades, avg win/loss, expectancy,
      sortino, calmar — added 2026-07-02, was summary-only before)
      DELETE /api/v1/trades/backtest-history/{id} — delete one run
      DELETE /api/v1/trades/backtest-history — delete all runs
      POST /api/v1/trades/backtest-record — run backtest + persist result in one call

### Phase 9 — Frontend Dashboard ✅ DONE

- [x] React 19 + TypeScript + TailwindCSS v4 + Vite 8
      frontend/ — npm run dev (port 5173), npm run build
      Vite proxy: /api → http://localhost:8000 (no CORS issues)

- [x] TradingView Lightweight Charts — candlestick chart on Dashboard

- [x] Pages: Dashboard, Signals, Backtest, Portfolio, Paper Trade, AI Chat, Settings
      src/pages/Dashboard.tsx   — live chart + signal + indicators, auto-refresh 60s
      src/pages/Signals.tsx     — any strategy/symbol/interval signal on demand
      src/pages/Backtest.tsx    — run + persist backtest, history table + pagination
      (rows-per-page 50/100/All), delete-row + delete-all (2x confirm), expandable
      per-row detail (winning/losing trades, avg win/loss, expectancy, sortino, calmar),
      "Backtest All Timeframes" button (loops all 8 intervals, sorted summary + detail,
      each run persists to history normally), inputs persisted via localStorage
      src/pages/Portfolio.tsx   — analytics + trade history with mode filter
      src/hooks/usePersistedState.ts — useState that survives refresh via localStorage,
      used by Backtest.tsx and PaperTrade.tsx form inputs (2026-07-02 fix — inputs were
      resetting to defaults on every page refresh)
      src/pages/PaperTrade.tsx  — start/stop paper engine, live position + trade log.
      Also shows GET /paper/orders (manual SignalCard-button trades) and
      GET /trades/history?mode=PAPER (durable DB history — survives backend
      restarts; the old page only showed the live engine's in-memory last-20,
      which looked like "trades not shown" whenever the process had restarted
      since the trade happened). Inputs persisted via usePersistedState.
      src/pages/AIChat.tsx      — multi-turn chat with suggested prompts. Error
      handling now surfaces the real backend error (e.g. "NVIDIA_API_KEY not
      set") instead of a canned message — "chat doesn't work" is almost always
      a missing NVIDIA_API_KEY in .env, not a code bug; check that first.
      src/pages/Settings.tsx    — env vars reference + phase completion status
      (Phase 10 was stuck at incomplete in the UI after Phase 10 shipped — fixed)

- [x] Components: SignalCard, PortfolioSummary, TradeTable, IndicatorPanel, RegimeBadge, Sidebar
      src/api/client.ts — typed axios API client for all backend endpoints

### Phase 10 — SaaS Platform ✅ DONE

- [x] JWT authentication (register, login, token refresh)
      File: backend/app/core/security.py (bcrypt hash + JWT encode/decode, tier claim embedded)
      File: backend/app/services/auth/auth_service.py — AuthService (register/login/refresh/API keys)
      File: backend/app/api/v1/auth.py — POST /auth/register, /auth/login, /auth/refresh, GET /auth/me
      File: backend/app/api/deps.py — get_current_user (JWT bearer OR X-API-Key header, either works)
      Uses `python-jose` for JWT, `bcrypt` directly for hashing (passlib's bcrypt backend
      is broken on bcrypt>=4.1 — do not reintroduce passlib for this)

- [x] Multi-user support — User model + auth exists; `trades.user_id` FK added (nullable) for
      future trade-history scoping. NOTE: paper/live trading engines are still process-wide
      singletons (PaperFactory/LiveTradingFactory) — not yet scoped per-user. Fine for one
      deployment per operator; would need per-user engine instances for true multi-tenant trading.

- [x] API key management
      DB: ApiKey model (backend/app/db/models.py) — key_hash (SHA-256) stored, never the raw key
      POST /auth/api-keys (returns raw key once), GET /auth/api-keys, DELETE /auth/api-keys/{id}
      Auth via X-API-Key header — same get_current_user dependency as JWT

- [x] Subscription tiers (free / pro / enterprise)
      User.tier field; GET /billing/tiers (public tier catalog + rate limits)

- [x] Billing integration (Stripe)
      File: backend/app/services/billing/stripe_service.py — checkout sessions + webhook sync
      POST /billing/checkout, GET /billing/subscription, POST /billing/webhook
      Requires STRIPE_SECRET_KEY / STRIPE_WEBHOOK_SECRET / STRIPE_PRICE_PRO / STRIPE_PRICE_ENTERPRISE
      Gracefully degrades to 503 if unconfigured (same pattern as AI services)

- [x] Rate limiting per user tier
      File: backend/app/core/rate_limit.py — slowapi, tier read from JWT claim (no DB hit)
      Applied via @limiter.limit(tier_rate_limit) decorator on: AI endpoints (all 6),
      /paper/start, /paper/order, /trading/start. Fixed 10/minute on /auth/register, /auth/login.
      NOTE: no global middleware — slowapi's SlowAPIMiddleware only supports static default
      limits, not per-request dynamic ones combined with middleware's in_middleware=True path
      (it skips per-route dynamic limits entirely). Decorator-per-route is the correct pattern.

- [x] Cloud deployment: Docker + docker-compose
      docker/backend.Dockerfile, docker/frontend.Dockerfile (multi-stage, nginx), docker/nginx.conf
      docker-compose.yml — postgres + backend + frontend, all env vars wired
      Run: `docker compose up --build` (needs .env — see .env.example)
      VERIFIED: both images built and run for real — alembic migrations apply, Kronos loads,
      FastAPI boots, live HTTP requests succeed inside the container; nginx correctly proxies
      to the backend service on the compose network.
      NOTE: no separate AWS/GCP IaC — docker-compose is the deployment artifact; push images to
      any container host (ECS, Cloud Run, etc.) manually or via CI
      NOTE: backend requires KRONOS_PATH mounted with the Kronos model repo's `model.py` present
      (sys.path.insert + `from model import ...` in kronos_service.py) — the whole app fails to
      boot without it, since main.py imports the Kronos singleton eagerly. Set
      KRONOS_PATH_HOST in .env to the real Kronos repo path on the host.

### Post-Phase-10 fixes/additions (2026-07-02, same day as Phase 10 — user reported a batch
  of frontend bugs + one new strategy after all 10 phases shipped):
  - **Backtest page overhaul**: was silently capped at `limit=20` server-side, no way to see
    more, no delete, missing interval/candles/time columns, inputs reset on refresh.
    Backend: `BacktestRun` model gained 7 detail columns (winning/losing trades, avg win/loss,
    expectancy, sortino, calmar — migration `1c9c073277cf`, needed `server_default='0'` on
    the SQLite batch-alter or it fails with "Cannot add NOT NULL column with default NULL").
    `/trades/backtest-history` now returns `{total,limit,offset,runs}` (limit up to 1000) +
    new `DELETE /trades/backtest-history/{id}` and `DELETE /trades/backtest-history` (all).
    Frontend: rows-per-page selector (50/100/All), delete-row + delete-all (2x-click confirm,
    4s window), expandable per-row detail, "Backtest All Timeframes" button (loops all 8
    intervals sequentially through the existing single-run endpoint — no new backend
    endpoint needed, each run persists to history normally), inputs persisted via
    `usePersistedState` (new hook, `src/hooks/usePersistedState.ts`).
  - **Paper Trading "bugs" — engine was NEVER broken.** Live-verified: started the auto-bot
    on 1m BTCUSDT, watched a real BUY → TAKE_PROFIT cycle execute end-to-end (backend log +
    DB row). The actual bug was frontend-only: `PaperTrade.tsx` only showed the live engine's
    in-memory `recent_trades` (capped at 20, reset on backend restart) and never showed
    `ManualPaperTrader` orders (the SignalCard "Place Paper Trade" button) at all — so trades
    that happened before a restart, or via the manual button, looked "not shown." Fixed by
    also fetching `GET /trades/history?mode=PAPER` (durable) and `GET /paper/orders` on the
    page. The engine is a server-side singleton — refreshing the browser never stopped it;
    that just wasn't visible before.
  - **AI Chat "bug" was a missing `NVIDIA_API_KEY`**, not a code bug — confirmed via direct
    curl to `/ai/chat` (503 with exact reason). Wiring (client → schema → backend) was
    already correct. Improved `AIChat.tsx`'s catch block to surface the real
    `error.response.data.detail` instead of a hardcoded generic message, so this
    self-diagnoses next time.
  - **Settings page phase list**: Phase 10 row was hardcoded `false` even though Phase 10
    had shipped — one-line fix.
  - **New strategy: CTA Trend** (`cta_trend_strategy.py`, factory key `cta_trend`) —
    "Systematic Trend Following" from the user's pasted TS reference. User pasted 5
    strategies (Turtle, CTA Trend, EMA Pullback, SMC, Engulfing Scalp) across two messages
    but asked for "one more strategy" — clarified via AskUserQuestion, user chose CTA Trend
    only; the other 4 were NOT implemented. Composite of 3 EMA-crossover pairs (10/50,
    20/100, 50/200) + 2 momentum sub-signals (90/180-bar), volatility-targeted confidence,
    ATR(20)-scaled stops (2.5x/4x) — independent of the shared DynamicATR regime table.
    New `IndicatorService.calculate_cta_trend()` method holds the composite math (kept
    calc logic out of the strategy file per the "IndicatorService calculates indicators"
    rule); all periods live in `strategy_config.py` as `CTA_*` constants. Verified live via
    direct test script + through the actual running API (`/strategy/signal`,
    `/trades/backtest-record`) — both work, numbers are sane (RR exactly matches the
    2.5/4.0 ATR ratio).
  - GOTCHA (recurring in this session): editing files does NOT reload a running
    `uvicorn` process without `--reload` — every backend code change needs a manual
    kill+restart before it's live-testable. Caught this twice (hit a stale
    `ValueError: Unknown strategy: cta_trend` from the pre-restart process).

  - **New strategies: Turtle Trading + Engulfing Scalp** (`turtle_strategy.py` key
    `turtle`, `engulfing_scalp_strategy.py` key `engulfing_scalp`) — user asked for these
    two by name in a follow-up message, pasting TS reference code for both. Both fully
    implemented, factory-registered, added to all 4 frontend strategy dropdowns
    (Signals/Backtest/PaperTrade/Portfolio) + `StrategySelectionRequest.available_strategies`.
    - Turtle Trading: Richard Dennis dual breakout. System 1 = 20-bar breakout, filtered
      by whether the LAST System-1 breakout in that direction was a loss (skips if it won,
      unless price also breaks the unfiltered 55-bar channel as failsafe). System 2 =
      55-bar breakout, always taken. N = ATR(20) ("volatility unit"), stops/targets fixed
      at 2N/4N → RR always exactly 2.0 when triggered. The last-breakout-loss filter does
      a backward historical scan (capped at `TURTLE_BACKWARD_SCAN_BARS=150`) — kept in the
      strategy file (trade-outcome logic), not IndicatorService. Slowest strategy on the
      platform: ~15s for a 500-candle backtest (O(n²) scan) — acceptable, but noticeably
      slower than the rest. Config: `TURTLE_*` in `strategy_config.py`.
    - Engulfing Scalp: long-only. Price > EMA200 AND RSI14 > 50 AND bullish engulfing
      candle on the last closed bar → BUY (never SELL). Stop/target sized off the
      engulfing candle's own range (not ATR): stop = entry − 2×range, target sized to a
      fixed RR of 2.0. +10 confidence bonus on bullish RSI divergence (price lower-low +
      RSI higher-low across last 2 swing lows in a 20-bar window). Config: `ENGULF_*`.
    - `IndicatorService` gained 3 methods to support these (all indicator-layer, per the
      "IndicatorService calculates indicators" rule): `calculate_atr_at_period(df, period)`
      (ATR at a caller-chosen window — the existing `calculate_from_dataframe` ATR is fixed
      at 14), `rolling_channel(df, period, exclude_current=True)` (highest-high/lowest-low
      over N *closed* candles — excludes the in-progress bar to avoid look-ahead bias),
      `calculate_rsi_series(df, period)` (full RSI series, needed for divergence scanning;
      the existing RSI calc only returns the latest scalar).
    - Verified via the same layered method used for CTA Trend: unit test with live
      BTCUSDT data (`tests/test_turtle_strategy.py`, `tests/test_engulfing_scalp_strategy.py`
      — both assert RR is exactly 2.0 when triggered, FLAT-safe on short history, correct
      factory resolution) → synthetic-data test forcing the BUY/SELL branch (live market
      often only produced FLAT) → live `/strategy/signal` API call → live
      `/trades/backtest-record` API call with timing (Turtle: 5 trades, −0.0434% return,
      15.3s/500 1h candles; Engulfing Scalp: 4 trades, −0.0253% return, 11.6s/500 candles).
    - `CLAUDE.md` Task 10 section updated to match (file list, factory keys, both strategy
      descriptions, corrected the stale "were NOT implemented" claim).

### Post-Phase-10 fix — Backtest/exit accuracy + time-to-target (2026-07-02)

User flagged that backtest results didn't feel trustworthy and asked for an ETA on
signals ("how long until target") so users can judge which timeframe suits a strategy.

- **Root cause found**: `ExitManager.check_exit()` only ever compared the candle's
  CLOSE price against stop_loss/take_profit/trailing levels — never the candle's
  high/low. A candle that wicked through a level and closed back on the other side
  was invisible to the backtest. Worse, the fill price on every exit was also the
  close price (with slippage), not the actual level — so TAKE_PROFIT exits could
  realize MORE than the intended target (close ran past it) and STOP_LOSS exits
  could realize a bigger loss than the intended risk (close gapped past it). This
  is why win rates/PnL looked inconsistent across strategies.
- **Fix**: `exit_manager.py` now takes optional `high`/`low` and checks STOP_LOSS,
  TAKE_PROFIT, PARTIAL_EXIT (1:1 RR), and TRAILING_STOP against the candle's full
  range, not just the close — these are "resting order" style exits where a wick
  matters. ATR_REVERSAL / TIME_EXIT / SIGNAL_REVERSAL stay close-based, since
  those are confirmed-on-close decision exits, not resting orders, by design.
  `check_exit()` now returns `(should_exit, reason, exit_price)` — a 3-tuple, up
  from 2 — fill price is the actual level touched, capped so a gap can't overstate
  a TAKE_PROFIT and using the worst of level/candle-extreme for a gapped-through
  STOP_LOSS. `TradeManager.should_exit()` threads `high`/`low` through and exposes
  `last_exit_price`. Applied to backtest (`simple_trading_engine.py`), paper
  trading (`paper_trading_engine.py` — real simulated fills, same bug), and live
  trading (`live_trading_engine.py` — detection only, since real fills come from
  Binance; this also fixes a live risk gap where a stop could be silently skipped
  if price wicked through it and closed back favorably). Re-ran Turtle at 1h/500
  candles post-fix: 0/7 win rate in a SIDEWAYS/WEAK_BEAR-dominated window — a
  legitimately harsher, more realistic result (breakout systems whipsaw in chop);
  previously this kind of run could look artificially better due to the close-only
  bug. `tests/test_exit_manager.py` + `tests/test_partial_exit.py` updated for the
  3-tuple return.
- **Time-to-target**: two complementary pieces, since a live signal has no trade
  history yet but a backtest does.
  - Live signals: `backend/app/services/strategy/eta_estimator.py` —
    `TimeToTargetEstimator.estimate()`, an ATR-velocity heuristic (no history
    needed): `candles ≈ reward_distance / (atr × ETA_ATR_PROGRESS_FACTOR ×
    regime_multiplier)`, since ATR is the full two-sided range and only part of
    it becomes net favorable progress per candle (config: `ETA_*` in
    strategy_config.py — damping factor + STRONG/WEAK/SIDEWAYS regime
    multipliers). Wired into `GET /strategy/signal` only (the one full-signal
    endpoint all display surfaces use) — `TradingSignal` gained
    `eta_candles`/`eta_display` (Optional, null on FLAT). Not duplicated into
    each of the 8 strategy files.
  - Backtests: `TradeResult` gained `entry_timestamp`/`exit_timestamp`/
    `candles_held`/`exit_reason` (`TradeRecorder` + `SimpleTradingEngine` now
    pass these through). `BacktestResult` gained `avg_candles_to_win` +
    `avg_time_to_win_display` — the actual measured average duration of winning
    trades, the empirical answer to "does this strategy suit this timeframe."
    Persisted: `BacktestRun` DB model gained the same 2 columns (migration
    `8f2b5a1d6c40`, nullable — no `server_default` needed since these are
    legitimately absent when a run has 0 wins). Surfaced as a new "Avg Time to
    Win" column on the Backtest page's history table — directly useful with the
    existing "Backtest All Timeframes" button for comparing timeframes at a
    glance.
  - Shared helper: `backend/app/core/time_utils.py` — `interval_to_minutes()`,
    `candles_to_display()` (candles+interval → "~X min/hr/days"), and
    `trade_duration_display()` (wall-clock diff of two ISO timestamps — used on
    `/trades/history` for PAPER/LIVE trades, which already had real
    entry/exit timestamps in the DB but never surfaced a human duration).
- Frontend: `SignalCard.tsx` shows "Est. Time to Target" next to Confidence/RR
  when present. `TradeTable.tsx` gained a Duration column. `Backtest.tsx`
  gained the Avg Time to Win column (`DetailRow` colSpan bumped 10→11).
  `client.ts` types updated for all of the above.

### Post-Phase-10 addition — Multi-strategy auto-scan + multi-timeframe scan (2026-07-02)

User wanted every strategy to analyze the market on its own (no manually opening
each one to test it), and every strategy's page to show signals across multiple
timeframes at once so a user can tell which timeframe a given strategy suits.

- New service: `backend/app/services/strategy/signal_scanner.py` — `SignalScanner`,
  two modes:
  - `scan_all_strategies(symbol, interval, limit)` — fetches market data ONCE,
    runs all 8 registered strategies against it concurrently
    (`ThreadPoolExecutor`, `SCAN_MAX_WORKERS` in config). One strategy's
    exception doesn't fail the batch — caught per-unit, returned as a FLAT
    signal with `error` set (new `Optional[str]` field on `TradingSignal`)
    rather than 500ing the whole scan.
  - `scan_timeframes(strategy, symbol, intervals, limit)` — one strategy,
    each interval fetched+run independently and concurrently (can't share
    market data across intervals — different candles). Default interval set:
    `SCAN_DEFAULT_INTERVALS` in strategy_config.py.
  - Both attach the same ATR-velocity ETA (`eta_estimator.py`, reused, not
    duplicated) to every non-FLAT result.
  - Concurrency matters here specifically because of Turtle's O(n²)
    backward-scan (~slowest strategy, ~ns per candle) — serial execution of
    8 strategies (or 6 timeframes) would make the scan feel broken; measured
    ~0.6–0.9s per scan with concurrency vs. what would be Turtle's own
    multi-second cost dominating a serial loop.
  - `StrategyFactory` gained a class-level `STRATEGIES` dict (was function-
    local) + `list_strategies()` — single source of truth for the scanner
    and the new `GET /strategy/available` endpoint.
- New endpoints in `backend/app/api/v1/strategy.py`:
  `GET /strategy/scan` (symbol, interval, limit → list[TradingSignal], one
  per strategy), `GET /strategy/multi-timeframe` (strategy, symbol,
  intervals csv optional, limit → list[TradingSignal], one per interval),
  `GET /strategy/available` (→ `{"strategies": [...]}`, the factory's key list).
- Frontend: `frontend/src/components/SignalScanTable.tsx` (NEW) — shared table
  for both scan modes (`labelKey: 'strategy' | 'interval'`), row click
  fires a callback. `Signals.tsx` rewritten: "Market Scan" panel (all
  strategies, one timeframe, auto-runs on symbol/interval change) +
  "Multi-Timeframe" panel (one strategy, every timeframe, auto-runs on
  strategy/symbol change) + the existing single SignalCard detail view below,
  which now stays in sync with whichever row was last clicked in either scan
  table. Clicking a strategy row needs the factory key (e.g. `rsi`) but
  `TradingSignal.strategy` is a human label (e.g. "RSI Strategy") — added a
  static `STRATEGY_LABEL_TO_KEY` map in `Signals.tsx` (labels don't derive
  mechanically from keys — e.g. "Bollinger Breakout" → `breakout`, "EMA
  Crossover" → `ema` — a naive lowercase/underscore transform is wrong for
  most of them, verified by grepping every strategy file's actual
  `strategy="..."` string before writing the map).
- `tests/test_signal_scanner.py` — asserts one signal per strategy/interval,
  no per-unit errors, correct interval/strategy set returned.
- Verified live via curl through both the raw backend and the Vite proxy
  (exact path the browser uses); no browser tool available to screenshot the
  actual rendered page this session.

### Post-Phase-10 addition — Chart infinite-scroll history (2026-07-03)

User asked what market API is used (Binance public REST via `python-binance`,
free/no-key — confirmed it already returns OHLCV + quote volume, which feeds
RSI/MACD/ADX/ATR/Bollinger/Supertrend/relative-volume in IndicatorService;
flagged but did NOT implement: Binance klines also return `number_of_trades` +
taker-buy volume for buy/sell pressure, currently dropped by `BinanceProvider`
— available if deeper volume analysis is wanted later) and why the Dashboard
chart only ever showed a fixed small batch of candles with no way to scroll
further back.

- Root cause: `Dashboard.tsx` called `getMarket(SYMBOL, INTERVAL, 150)` once
  on mount — no pagination existed anywhere in the stack (backend always
  fetched the LATEST `limit` candles, no way to ask for older ones).
- Backend: added optional `end_time` (unix ms) through the whole chain —
  `BaseMarketProvider.get_market_data(..., end_time=None)` →
  `BinanceProvider` passes it as Binance's own `endTime` kline param (native
  backward-pagination support, nothing custom) → `MarketService` → `GET
  /market/history?...&end_time=...`. When given, returns `limit` candles
  ending at/before that timestamp instead of the most recent ones. Verified
  no boundary overlap (end_time = oldest_loaded_ms − 1).
- Frontend: `Dashboard.tsx` chart now keeps the full loaded candle array in
  a closure var, subscribes to `chart.timeScale().subscribeVisibleLogicalRangeChange()`,
  and once the visible range comes within `LOAD_MORE_THRESHOLD_BARS` (20) of
  the oldest loaded bar, fetches another `PAGE_CANDLES` (500) page via
  `end_time`, dedupes, prepends, `setData()`s the merged array, then restores
  the visible logical range shifted by the newly-added bar count (lightweight-
  charts doesn't preserve scroll position across `setData()` on its own).
  Initial load bumped 150 → 500 candles. Small "Loading older candles…" /
  "Full history loaded" status line above the chart.
- `client.ts` `getMarket()` gained an optional `endTime` param.
- No other market providers exist (`ProviderFactory` only registers
  `binance`), so this was a single-provider change — no fan-out risk.

### Post-Phase-10 addition — AI-Based Automatic Pattern Recognition (2026-07-03)

> **SUPERSEDED (2026-07-04):** the 8 classical chart-shape detectors
> described in this section (Double/Triple Top, Head & Shoulders, Triangle,
> Wedge, Flag/Pennant, Channel/Rectangle, Cup & Handle, Diamond/Broadening)
> were **deleted** by explicit user request and replaced with a full
> candlestick-pattern engine (~32 patterns). See "Candlestick pattern engine
> replaces classical chart-shape detectors" further down for the current
> state. FVG and SMC (also described below) were NOT touched — still exactly
> as documented here. This section is kept for history/context on the
> shared foundation (`SwingDetector`, `trendline.py`, `pattern_utils.py`,
> `PatternFactory`/`PatternScanner` architecture) that the new engine reuses
> unchanged.

User's full spec: automatic multi-pattern chart detection (~20 classical patterns),
FVG, SMC (order blocks/BOS/CHOCH/liquidity), multi-timeframe, AI explanation +
recommendation per pattern, chart annotation overlay, a pattern dashboard. Given
the scope, asked the user to pick v1 breadth vs. depth — they chose **full breadth
now** (all pattern families + AI auto-generated for every detected pattern, not
on-demand), so that's what got built, with the tradeoffs that implies (documented
below) rather than silently narrowed.

**New domain**: `backend/app/services/pattern/` — mirrors the strategy layer's
separation rule (detectors only detect structure, never decide what to do about
it; AI only explains/recommends, never re-detects).

- **Foundation** (shared by nearly every detector):
  `swing_detector.py` — fractal pivot highs/lows (strict local max/min within a
  lookback window on both sides). `trendline.py` — least-squares line fit over
  swing points + slope classification (FLAT/RISING/FALLING, tolerance-based).
  `pattern_utils.py` — id generation, `status_from_breakout()` (DEVELOPING/
  CONFIRMED/BROKEN from price vs. breakout/invalidation levels + ATR margin),
  `measured_move_targets()` (T1 = pattern's own measured move, T2/T3 = fib-style
  extensions at 1.618x/2.618x), `algorithmic_confidence()` (weighted: geometry
  fit 40% + volume confirmation 25% + breakout strength 20% + pattern size 15%,
  weights in `pattern_config.py`).
- **FVG**: `fvg_detector.py` — standard 3-candle imbalance (low[3] > high[1] =
  bullish, mirrored for bearish), filled/unfilled tracked by scanning forward for
  a candle that trades back into the gap, strength scaled by gap-size/ATR ratio.
- **SMC**: `smc_detector.py` — trend inferred from swing sequence (higher-highs
  +higher-lows = UP, mirrored for DOWN); a break of the most recent swing
  high/low is BOS if it continues that trend, CHOCH if it contradicts it (first
  sign of reversal). Order block = last opposite-colored candle before the break.
  Liquidity zones = clusters of equal highs ("buy-side", bearish bias once
  swept) / equal lows ("sell-side", bullish bias once swept), tolerance-based.
- **8 classical pattern families**, each its own file (300-500 line class cap):
  `double_triple_patterns.py` (Double/Triple Top/Bottom — consecutive
  roughly-equal swing extremes with a deep-enough retracement between them),
  `head_shoulders_detector.py` (H&S/Inverse — 3 extremes, middle one more
  extreme than two roughly-equal outer ones, neckline is a fitted 2-point line
  through the troughs), `triangle_detector.py` (Asc/Desc/Symmetrical —
  resistance+support trendline slope combination, must be converging by
  `TRIANGLE_MIN_CONVERGENCE_PCT`), `wedge_detector.py` (Rising/Falling — BOTH
  lines same-direction-sloped while converging, the distinguishing feature vs.
  a triangle), `flag_pennant_detector.py` (a flagpole move of
  `FLAGPOLE_MIN_MOVE_PCT`+ followed by a shallow consolidation; parallel-width
  consolidation = flag, narrowing = pennant), `channel_rectangle_detector.py`
  (flat/flat = rectangle, same-slope-and-parallel = channel — the "must stay
  parallel not converge" check is what separates this from wedge/triangle),
  `cup_handle_detector.py` (U-shaped quadratic fit between two comparable rims,
  R²≥0.5 + vertex roughly centered; optional shallow handle pullback after —
  present = Cup & Handle, absent = Rounding Bottom), `diamond_broadening_detector.py`
  (Broadening = resistance rising + support falling, i.e. expanding not
  converging; Diamond = a broadening first half that contracts into a triangle
  second half). Symmetrical Triangle / Rectangle / Diamond / Broadening are
  direction-NEUTRAL by nature (only certain once actually broken) — each
  detector documents which side it treats as the primary watched breakout as a
  deliberate, disclosed simplification, not a hard technical-analysis rule.
- **Orchestration**: `pattern_factory.py` (mirrors `StrategyFactory` — class-level
  `DETECTORS` dict + `list_detectors()`). `pattern_scanner.py` — `SignalScanner`
  the pattern-module answer: `scan()` fetches market data ONCE and runs every
  detector concurrently (`ThreadPoolExecutor`, pure CPU work, sub-second);
  `scan_multi_timeframe()` runs `scan()` per interval concurrently;
  `dashboard()` flattens+sorts by confidence across timeframes. A single failed
  detector doesn't kill the batch (caught, returns `[]` for that detector only).
- **AI**: 8th AI service (of 7 documented in Phase 5) —
  `backend/app/services/ai/pattern_explainer.py`, `PATTERN_EXPLAINER` in
  `ai_provider_config.py` (Nemotron, thinking off — same "fast/cheap, called a
  lot" rationale as Market Analyst, since this one runs once per pattern per
  scan, not once per scan). Every pattern clearing `PATTERN_SCAN_MIN_CONFIDENCE`
  (40%) gets `why_detected`/`why_valid`/`market_psychology`/
  `buyer_seller_behavior`/`strength`/`reliability_score`/`alternative_scenario`/
  `recommendation` (BUY/SELL/WAIT/AVOID)/`recommendation_reason` auto-generated.
  Graceful degradation: if `NVIDIA_API_KEY` isn't set, patterns still return
  with full algorithmic data, just `ai.error` set instead of failing the scan.
- **Endpoints**: `GET /patterns/scan`, `/patterns/multi-timeframe`,
  `/patterns/dashboard`, `/patterns/available` — `backend/app/api/v1/patterns.py`.
- **Frontend**: `PatternAnalysis.tsx` (NEW page, `/patterns`) — chart with real
  annotation drawing (`LineSeries` per trendline, `createPriceLine` for
  levels/zone boundaries/SL/targets, `createSeriesMarkers` for text labels —
  all via lightweight-charts v5's actual plugin APIs, not a placeholder) +
  pattern list + `PatternInfoPanel.tsx` (NEW component, every field from the
  spec's "Pattern Information Panel"/AI Explanation sections). `PatternDashboard.tsx`
  (NEW page, `/patterns/dashboard`) — the flattened cross-timeframe table,
  confidence slider, row click routes to `/patterns?symbol=&interval=` (read via
  `useSearchParams`, pre-fills that exact chart). Both added to `Sidebar.tsx` + `App.tsx`.
  Dashboard scan does NOT auto-run on mount (explicit button) — it's the
  most expensive call in the app (see performance note below).
- Also added `1w` (weekly) to `BinanceProvider.INTERVAL_MAP` — the user's spec
  asked for it and it genuinely wasn't there before (max was `1d`).

**Real bugs found and fixed while building this** (not hypothetical — each one
reproduced live and verified fixed):
- **numpy 2.2.6 / pandas 3.0.4 segfault**: `pd.Timestamp(<numpy.datetime64 from
  .to_numpy()>)` crashes the whole Python process (`Segmentation fault (core
  dumped)`), and separately `pd.date_range()` itself also segfaults in this
  environment. Root cause is a C-extension incompatibility in this specific
  numpy/pandas combo, not application logic — existing code never hit it because
  it always converts timestamps via `df["timestamps"].iloc[i].isoformat()`
  (pandas' own indexing, already a proper `Timestamp`), never by pulling a raw
  scalar out of `.to_numpy()` and rewrapping it. Fix used everywhere in the new
  pattern code: call `.item()` on the numpy scalar first (native Python
  `datetime`, safe) before `.isoformat()`. For synthetic test data, build
  timestamp lists with plain `datetime + timedelta`, never `pd.date_range()`.
  Worth remembering for ANY future code that does `.to_numpy()` on a timestamp
  column in this environment.
- **Cup & Handle right-rim detection**: originally used "highest point in a
  generous window after the bottom," which — verified via a synthetic
  forced-cup test — picked up a peak from inside the trailing handle-search
  region instead of the cup's actual completion point (RR came out to 85.6,
  an obvious tell). Fixed by anchoring the right rim to an actual swing-high
  (fractal pivot, via `SwingDetector`) closest to the left rim's price level,
  not a raw threshold-crossing or unbounded argmax — re-verified correct
  (RR 6.32) after the fix.
- **AI concurrency wasn't actually global**: `PATTERN_AI_MAX_WORKERS` (4) was
  enforced by a fresh `ThreadPoolExecutor` created inside every `scan()` call —
  but `scan_multi_timeframe()` runs multiple `scan()` calls concurrently too, so
  actual concurrent NVIDIA requests multiplied (up to ~32 in testing) instead of
  staying capped at 4. Measured live: 38 of 54 patterns got `HTTP 429 Too Many
  Requests` across a full 9-timeframe scan. Fixed by making the AI thread pool
  a single instance shared for the scanner's whole lifetime (created once in
  `PatternScanner.__init__`, submitted to by every `scan()` call, matching how
  `scanner = PatternScanner()` is a module-level singleton in `patterns.py`
  anyway) plus a 2-retry backoff on `openai.RateLimitError`. Re-verified: 0
  errors across the same 9-timeframe scan after the fix.

**Known gaps — designed into the schema but not implemented, said plainly rather
than silently omitted**: `DetectedPattern.historical_success_rate`,
`expected_time_to_target`, `pullback_zone_low/high` are real Optional fields in
`schemas/pattern.py` (per the spec's "Historical Success Rate," "Expected Time
to Reach Target," "Possible Pullback Zones" asks) but no detector currently
populates them — they'll always be `null` today. `expected_time_to_target`
could reuse the existing `TimeToTargetEstimator` from the Signals ETA feature
fairly cheaply (needs an ATR value threaded onto `DetectedPattern` first);
historical_success_rate would need a backtest-style forward-scan per pattern
type, more work. Diamond Pattern reuses the same validated trendline-fit/
slope-classify primitives as Triangle/Wedge/Channel (all independently
synthetic-tested) but wasn't itself given a dedicated synthetic positive-path
test — lower confidence than the other 8 detectors, not because the logic
looks wrong, just less scrutinized (diamonds are also genuinely rare, hardest
pattern to construct a clean synthetic example for quickly).

**Performance — the direct, disclosed cost of "AI for every pattern, not
on-demand"**: single-timeframe `/patterns/scan` with patterns found: several
seconds up to about a minute, dominated by AI calls at the concurrency cap, not
detection (detection alone across all 9 detectors is sub-second). Full
`/patterns/dashboard` (9 timeframes): ~1-2 minutes, measured live at 2m14s for
54 AI-enriched patterns. This is why the dashboard button doesn't auto-fire on
page load. If this becomes annoying in practice, the fix is switching the AI
trigger to on-demand-per-click (the originally recommended, not chosen, option)
rather than tuning concurrency further — concurrency is already correctly
capped at NVIDIA's actual rate limit now.

### Post-Phase-10 addition — Analysis Tools Phase 1 (2026-07-03)

User's full ask: 12 major tool categories (Price Action, Volume Profile, Footprint
Charts, Supply/Demand, Market Structure, Volume, Market Profile, S/R, Moving
Averages, VWAP, Pivots, ATR), a replay-based "Playground," individual toggle
buttons + an (ⓘ) help panel per tool, and AI confidence/bias/reasoning "for every
enabled tool." Given the size (~10-20x the Pattern Analysis module), asked the
user to scope via AskUserQuestion before writing code — got no response after
60s, proceeded on my own stated recommendations rather than block or guess
blindly:
- **Footprint Charts deferred** — needs bid/ask trade-level volume data
  (Binance's aggTrades stream, `isBuyerMaker` flag), which nothing in this
  codebase fetches today. Klines (100% of current data pipeline) don't have it.
  Not attempted — would have meant faking it.
- **AI is on-demand, not auto-per-tool** — the Pattern module already proved
  (previous session) that auto-AI at scale hits NVIDIA rate limits hard. This
  request's volume (~18 tools × Playground replay steps) would be 10-100x that.
  One AI call synthesizes confluence across whichever tools are enabled, fired
  by a user click, never automatically.
- **Phase 1 = B-tier only**: Support & Resistance, Moving Averages, VWAP, Pivot
  Points, ATR. Pure algorithmic, zero data blockers, fast to build correctly —
  and used to establish the toggle-button + Information-panel UI pattern once,
  meant to be reused for every future tool (S-tier, A-tier, remaining B-tier).
  S-tier (Price Action, Volume Profile), A-tier (Supply/Demand, Market
  Structure — note Market Structure's BOS/CHOCH/swing-points are ALREADY built,
  just living in the Pattern module's `SMCDetector`, not exposed as a
  standalone toggleable tool yet), Market Profile, Volume indicator, and the
  Playground itself are NOT built — explicitly deferred, not silently dropped.

**New domain**: `backend/app/services/analysis/` — separate from
`services/pattern/` (patterns detect *shapes*, these tools compute
*indicator-style overlays*), but reuses its foundation: `SwingDetector`,
`ChartAnnotations` schema, `pattern_utils.py` helpers (`now_iso`, id gen).
`base_analysis_tool.py` — `analyze(df, symbol, interval) -> AnalysisToolResult`,
same "algorithmic only, no AI" separation as every other detection layer.

- `support_resistance.py` — swing highs/lows clustered by tolerance into
  levels (touch count = strength), plus psychological round-number levels
  near current price. Bias leans toward whichever side (support/resistance)
  price sits closer to.
- `moving_averages.py` — EMA/SMA/WMA at 20/50/100/200 (WMA via
  `pandas_ta.wma()`, new — wasn't in `IndicatorService` before). Golden/Death
  Cross use SMA50/SMA200 specifically (the standard convention, not EMA).
  Chart draws only EMA20/EMA50/SMA50/SMA200 by default (all 12 series would
  be unreadable) — all 12 values still returned in `data` for the info panel.
- `vwap_tool.py` — Daily VWAP (anchored to start of current UTC day, found by
  scanning for the date change) + Anchored VWAP (auto-anchored to the most
  recent swing point via `SwingDetector` — no manual anchor drawing) + 1/2
  stddev bands on both (volume-weighted variance).
- `pivot_points.py` — Classic/Fibonacci/Camarilla/Woodie/DeMark, all computed
  from the prior FULL DAILY period's O/H/L/C regardless of the chart's own
  interval (fetches a separate `1d`-interval, 2-candle request internally —
  the professional convention, daily pivots shown on any intraday chart, not
  recomputed per-bar). Only Classic's 7 levels drawn on chart by default; all
  5 systems' full data returned for the info panel.
- `atr_tool.py` — wraps existing `IndicatorService.calculate_atr_at_period`,
  adds Low/Medium/High volatility classification (ATR as % of price) +
  suggested SL/TP for both long and short at ATR multiples (config-driven,
  `ATR_SL_MULTIPLIER`/`ATR_TP_MULTIPLIER`). Direction-NEUTRAL by design — this
  tool measures risk, not bias.
- `analysis_factory.py` + `analysis_scanner.py` — mirrors
  `pattern_factory.py`/`pattern_scanner.py`'s shape, concurrent
  (`ThreadPoolExecutor`), but deliberately has NO auto-AI (see above).
- 9th AI service: `backend/app/services/ai/analysis_explainer.py`
  (`ANALYSIS_EXPLAINER` config, Nemotron/thinking-off) — takes N already-
  computed tool results, makes ONE call synthesizing confluence (agreement/
  disagreement across tools), not one call per tool.
- Endpoints: `GET /analysis/available`, `GET /analysis/scan` (fast, no AI),
  `POST /analysis/explain` (on-demand AI, body = symbol/interval/tool_keys).
- Frontend: `ToolToggleBar.tsx` (individual buttons, each with its own (ⓘ) —
  "do not group into one menu" per the ask) + `ToolHelpPanel.tsx` (full
  What-is-it/How-it-works/How-to-use/Real-Example/Pro-Tips structure per
  tool, content authored in `data/toolHelpContent.ts`) + wired into
  `PatternAnalysis.tsx` (chart now draws BOTH the selected pattern's
  annotations AND every enabled tool's annotations simultaneously, merged
  into one marker/line/price-line set redrawn together — reuses the same
  lightweight-charts drawing helpers, refactored into `drawTrendlines`/
  `drawLevelsAndZones` functions shared between pattern and tool rendering).

**2 real bugs found and fixed during the mandated pre/post-implementation
testing** (both genuinely reproduced, not hypothetical):
- **`/trades/history` was 500ing on every call** — `trade_duration_display()`
  (built in an earlier session's "time-to-target" feature, not this one)
  crashed subtracting a tz-naive datetime (candle-sourced `entry_timestamp`)
  from a tz-aware one (`datetime.now(timezone.utc)`-sourced `exit_timestamp`)
  — exactly the pairing real trade rows have. Fixed by normalizing both to
  UTC-aware before subtracting. Found by the pre-implementation test pass
  this request explicitly asked for — would have shipped broken otherwise.
- **AI JSON parsing was all-or-nothing** — caught live: the model emitted
  near-valid JSON with one dropped closing quote (`"market_bias": "BULLISH,`)
  and a stray duplicate key; the naive `json.loads()` failure discarded the
  ENTIRE response (8 other valid fields lost over 1 glitched one). Added a
  regex-based per-field salvage fallback in `AnalysisExplainer._parse_json`
  for when strict parsing fails — a known, recurring LLM failure mode, not a
  one-off. `PatternExplainer` doesn't have this same hardening yet (worth
  backporting if it's seen there too).

**Testing performed** (both required by this request, both done): pre-
implementation — all 39 then-existing test files run, found the trades/history
bug. Post-implementation — all 41 test files (39 + 2 new:
`test_analysis_tools.py`, plus re-ran `test_pattern_scanner.py`) pass, zero
regressions. Full endpoint sweep across every API area (market/indicator/
strategy/portfolio/trades/paper/live/auth/billing/ai/patterns/analysis) all
return correct status codes. Frontend typechecks clean, Vite serves every new
file, both backend/frontend processes confirmed single-instance and healthy,
backend log clean of errors/tracebacks.

### Post-Phase-10 fix — Pattern Analysis infinite scroll + real FVG rectangles (2026-07-03)

Two follow-ups on the Pattern/Analysis modules, both from direct user feedback:

- **Chart stopped loading past ~400-500 candles on the Patterns page** —
  unlike Dashboard.tsx (already fixed earlier), `PatternAnalysis.tsx` never
  got the backward-pagination logic. Ported it over (same `end_time`-based
  approach, `subscribeVisibleLogicalRangeChange`), plus added an in-memory
  page cache (`Map` keyed by symbol/interval/end_time/limit) so re-scrolling
  back and forth over an already-visited range doesn't re-hit Binance.
- **Detectors were internally capped well below what got fetched** — even
  with more candles loaded on the chart, `FVGDetector`/`SMCDetector`/S&R/
  classical patterns each re-sliced to their own small hardcoded lookback
  window (FVG was 300 bars, SMC 150, S&R 200 — regardless of how much data
  the caller fetched). Bumped these in `pattern_config.py`/`analysis_config.py`
  to scale with the real per-request ceiling (1000, matching Binance/backend's
  own max) — FVG/S&R/SMC to 1000/1000/500, classical shape patterns
  (Double Top, H&S, Triangle, Wedge, Channel, Diamond/Broadening) to 300-400.
  Left Cup&Handle/Flag/Pennant lookbacks alone deliberately — those patterns
  have a real, bounded max duration by definition; scaling them up wouldn't
  find more valid patterns, just waste cycles. Verified fast even at 1000
  candles (full pattern-detector suite ~2.1s, analysis tools ~1s).
- **Scan limit now scales with loaded history**: `scanLimit = min(max(loaded, 500), 1000)`
  in `PatternAnalysis.tsx`. Analysis tools (no auto-AI) rescan automatically
  as more history loads, debounced 1.2s. Pattern detection deliberately does
  NOT auto-rescan on scroll (its scan auto-generates AI per pattern — see the
  rate-limit lesson from the Pattern module's own build) — stays on the
  existing manual "Rescan" button, which now just uses the current
  `scanLimit` instead of a hardcoded 400. Confirmed live: more history →
  proportionally more patterns/FVGs found → proportionally more AI-explain
  calls → longer full-scan wall time (22 patterns vs 11 at the old lookback,
  same test data) — this is the correct, disclosed tradeoff, not a
  performance regression in detection itself.
- **FVG zones (and every other zone-type annotation — order blocks, entry
  zones, consolidation ranges) now render as real filled/bordered
  rectangles**, not two dashed price lines. `frontend/src/lib/rectanglePrimitive.ts` —
  a hand-implemented lightweight-charts v5 series primitive (canvas
  `fillRect`/`strokeRect`, live time/price → pixel conversion so it tracks
  pan/zoom automatically) — the library has no built-in shaded-box primitive,
  had to build one. Watch for `erasableSyntaxOnly` in this project's
  tsconfig — constructor parameter-property shorthand
  (`constructor(private x: T)`) is rejected, use explicit field
  declarations + manual assignment instead.
- **FVG added as a proper toggle tool** (`fvg_tool.py`, wraps the existing
  `FVGDetector`) — was previously only a passive count on the Patterns page,
  now has its own button, chart zones, (ⓘ) help panel, and AI confluence
  participation, matching the other 5 Analysis Tools.

### Post-Phase-10 fix — Pattern scan timeout (2026-07-03) + AI client hardening

User: "pattern scan is failing most of the time." Root-caused via live testing
(not guessed): a fresh `/patterns/scan?limit=500` call on BTCUSDT/1h took
50-90+ seconds and sometimes returned nothing inside a 90s window — well past
the frontend's 30s axios timeout, which is exactly what "failing" looked like.

- **Actual cause**: the lookback-window bump from the previous fix (finding
  "all historical patterns") worked exactly as intended — 22-31 patterns
  found now vs. 11 before on the same data. But `/patterns/scan` still
  auto-generated an AI explanation for EVERY pattern found, sequentially in
  batches of `PATTERN_AI_MAX_WORKERS=4`. More patterns found → proportionally
  more AI-call batches → total time scaled with pattern count, not candle
  count. This is the same on-demand-vs-auto tradeoff already applied to
  Analysis Tools' AI confluence — just not yet applied to patterns when the
  module was first built.
- **Fix**: `PatternScanner.scan()`/`scan_multi_timeframe()` gained an
  `include_ai: bool = False` param — algorithmic-only and fast by default now
  (confirmed 2.5-4s consistently, vs. 50-90s before). New
  `PatternScanner.explain_pattern(pattern)` + `POST /patterns/explain` —
  on-demand AI for exactly the one pattern a user has selected, not the whole
  batch. `dashboard()` hardcodes `include_ai=False` unconditionally (its row
  schema never surfaced AI fields anyway — was wasted work before, not just
  slow). `include_ai=True` still available as an explicit opt-in on
  `/patterns/scan`/`/multi-timeframe` for anyone who wants the old
  all-at-once behavior. Frontend: `PatternAnalysis.tsx` now fetches AI
  on-demand per selection (`explainPattern()`, cached by pattern id so
  re-selecting is instant), `PatternInfoPanel.tsx` shows a "Generating AI
  analysis…" state meanwhile.
- **Also found while debugging (real, separate issues, both fixed)**:
  (1) the `openai.OpenAI` client had NO request timeout configured anywhere
  — the SDK's own default is effectively unbounded, and a `ThreadPoolExecutor`
  worker blocks on `.result()` until the call returns, so one slow/degraded
  NIM response could stall an entire concurrent scan indefinitely with no
  way to recover. Added `AI_REQUEST_TIMEOUT_SECONDS=20` (env-overridable) +
  `AI_SDK_MAX_RETRIES=1` to `ai_provider_config.py`, applied in
  `llm_client.py`'s `MultiProviderAIService.__init__` — this fixes ALL 9 AI
  services at once, not just patterns. (2) Found (again) a leftover orphaned
  `uvicorn` process from an earlier `pkill`-based restart that never actually
  died, pegged at ~95% CPU competing with the real server for the GIL/CPU —
  a red herring during this debugging session (fixed the real bug too, but
  this wasn't the actual cause), but a reminder: after `pkill`, verify with
  `ps aux | grep uvicorn` before trusting a restart, don't assume the kill
  landed. (3) Backported the JSON-parsing regex-salvage fallback (built for
  `AnalysisExplainer` a few turns ago) to `PatternExplainer` too — same
  malformed-JSON failure mode is possible in both, only one had the fix.

### Post-Phase-10 addition — User-entered Binance API keys (2026-07-04)

User wants to use their own Binance account for live trading, entered from
the Settings page rather than only via `.env`.

- **No login UI exists** (confirmed by investigation — backend JWT auth
  routes exist since Phase 10, but frontend has zero login page/AuthContext/
  token-attaching axios interceptor). Building full per-user credential
  scoping would require that auth UI first, which wasn't asked for. Given
  `LiveTradingFactory`/`PaperFactory` are already process-wide singletons
  (not per-user — documented Phase 10 limitation), a **single global
  encrypted credential row** matches the app's actual current
  single-operator reality, not a design regression.
- New DB model `ExchangeCredentials` (`backend/app/db/models.py`) — one row
  per exchange (`exchange` unique), `api_key_encrypted`/`api_secret_encrypted`
  (Fernet, not hashed — unlike `ApiKey`'s SHA-256, these must be recoverable
  in plaintext to hand to the Binance SDK), `key_preview` for UI display.
  Migration `2b6f9a4d1e73`.
  `core/security.py` gained `encrypt_secret`/`decrypt_secret` — Fernet key
  derived from `ENCRYPTION_KEY` env var if set, else derived from
  `JWT_SECRET` (no new required env var; `cryptography` was already a pinned
  dependency, unused directly until now).
- `backend/app/db/repository/credentials_repo.py` (upsert/get/delete) +
  `DatabaseService.save_exchange_credentials`/`get_exchange_credentials`/
  `get_exchange_credentials_status`/`delete_exchange_credentials`.
- New endpoints: `POST/GET/DELETE /api/v1/settings/binance-keys(/status)`
  (`backend/app/api/v1/settings.py`). No auth dependency — consistent with
  the rest of this app's currently-unauthenticated frontend calls.
- `BinanceExecution.__init__` and `LiveTradingEngine.start`/`_init_components`
  now accept optional `api_key`/`api_secret` params; `POST /trading/start`
  fetches decrypted DB credentials first (only when `dry_run=False`) and
  passes them through — falls back to `BINANCE_API_KEY`/`BINANCE_SECRET` env
  vars if no DB row exists, so existing env-only setups keep working
  unchanged.
- Frontend: `Settings.tsx`'s previously-cosmetic, unwired "API Connection"
  card replaced with a real form (masked password inputs, save/status/remove,
  remove uses the same 2-click-confirm pattern as Backtest's "Delete All
  History"). `client.ts` gained `getBinanceKeyStatus`/`saveBinanceKeys`/
  `deleteBinanceKeys`.
- Verified: encrypt/decrypt roundtrip, full repo CRUD (`tests/test_exchange_credentials.py`,
  new), FastAPI route registration (`/api/v1/settings/binance-keys*` present
  in the live OpenAPI schema), all 41 pre-existing test files still pass
  (zero regressions), frontend `tsc --noEmit` clean.

### Post-Phase-10 addition — Trend Line analysis tool (2026-07-04)

User wanted a way to see the market's overall trend on the Pattern Analysis
page. Added as the 7th Analysis Tool (`backend/app/services/analysis/trend_tool.py`,
factory key `trend`) — same architecture as the other 6 (algorithmic-only,
no AI in detection; `AnalysisFactory`/`AnalysisScanner`/toggle-bar/help-panel
all generic, so this needed zero special-case frontend code beyond a color
map entry + help content).

- Direction/strength: least-squares regression line through closes over the
  lookback window (`TREND_LOOKBACK_BARS=300`), slope normalized to %/bar,
  R² used as "trend fit strength." Reuses the existing `fit_trendline`/
  `classify_slope`/`slope_pct_per_bar` primitives from `pattern/trendline.py`
  (already used by Triangle/Wedge/Channel detectors) rather than duplicating
  regression math.
- Bias: swing structure (last 2 swing highs/lows via `SwingDetector` — HH+HL
  = BULLISH, LH+LL = BEARISH, mixed = NEUTRAL) takes priority when at least
  2 highs and 2 lows exist; falls back to the regression slope's direction
  otherwise (e.g. early in a dataset, or a driftless/very short window).
- Channel: when ≥2 swing highs AND ≥2 swing lows exist, also fits and draws
  a resistance line through the highs and a support line through the lows
  (`TREND_MIN_SWINGS_FOR_CHANNEL=2`) — gives a visual channel, not just one
  line. A clean monotonic move with no real swings correctly draws only the
  main trend line, no channel (verified in the synthetic test below, not
  assumed).
- Annotation labels are static (`trend_line`/`trend_resistance`/`trend_support`,
  not dynamic strings) specifically so they map cleanly in the frontend's
  `TOOL_LINE_COLORS` — dynamic per-render label text (e.g. embedding the
  slope %) would never match a static color-map key.
- `tests/test_trend_tool.py` — factory registration, a synthetic monotonic
  uptrend (asserts BULLISH/RISING/high-fit/no-channel), a synthetic
  oscillating uptrend (asserts HH/HL structure + full channel), and a live
  BTCUSDT/1h scan. Hit the numpy/pandas segfault gotcha again while writing
  this (see the Pattern Recognition section above) — but a new variant:
  building the synthetic DataFrame with **tz-aware** (`timezone.utc`)
  Python `datetime`s doesn't segfault, but does silently produce a
  tz-aware `datetime64` column whose `.to_numpy()` returns an object array
  of `Timestamp`s (not real `numpy.datetime64` scalars) — `SwingDetector`'s
  `times[i].item()` then throws `AttributeError: 'Timestamp' object has no
  attribute 'item'`, since `Timestamp` has no `.item()`. Real market data
  timestamps are tz-naive, so synthetic test data must be too — switched to
  naive `datetime(2026, 1, 1)` (no `tzinfo`) and it matched real data's
  dtype/behavior correctly.
- Verified: full `AnalysisScanner.scan()` (all 7 tools) returns zero errors
  including `trend`; all 43 test files (41 prior + this + the same-session
  exchange-credentials test) pass; frontend `tsc --noEmit` clean.

### Candlestick pattern engine replaces classical chart-shape detectors (2026-07-04)

User's explicit instruction: delete all 8 classical chart-shape detectors
(Double/Triple Top, Head & Shoulders, Triangle, Wedge, Flag/Pennant,
Channel/Rectangle, Cup & Handle, Diamond/Broadening) and replace them with
~32 candlestick patterns from a pasted reference table (pattern, detection
rules, confirmation, entry, stop, target, notes — one row per pattern).
Confirmed via AskUserQuestion before touching anything, since deleting 8
tested/working detectors is exactly the kind of hard-to-reverse call this
project's instructions say to check first — user explicitly chose "delete,
candlesticks only" and "all ~32 at once" over the safer phased/keep-both
defaults offered.

**Architecture — reused, not rebuilt.** The existing pattern-module
foundation turned out to fit almost perfectly with zero schema changes:
`DetectedPattern` (status DEVELOPING/CONFIRMED/BROKEN, breakout_level/
invalidation_level, entry_zone, stop_loss, target_1-3, `ChartAnnotations`
with trendlines/zones/levels/labels), `BasePatternDetector.detect(df,
symbol, interval) -> list[DetectedPattern]`, `PatternFactory`/
`PatternScanner` (concurrent multi-detector scan, on-demand AI explain, one
shared AI thread pool) — none of this needed to change. Only
`PatternFactory.DETECTORS` was swapped: the 8 old keys →
`single_candle`/`two_candle`/`three_candle` (SMC + FVG untouched, they're a
separate feature, not a "chart shape").

- **`backend/app/services/pattern/candlestick_utils.py`** (NEW) — shared
  per-candle metrics (`CandleMetrics`: body/upper_wick/lower_wick/
  total_range/is_bullish/midpoint) computed once and reused by every
  pattern check, instead of 32 copies of wick/body math. Also: `is_marubozu`/
  `is_doji`/`is_long_lower_wick`/`is_long_upper_wick`/`wick_at_least`/
  `roughly_equal`/`gapped_up`/`gapped_down`/`higher_volume`, and
  `local_trend(df, idx)` — a short-window least-squares slope read (reuses
  `fit_trendline`/`classify_slope` from the Trend Line tool's
  `pattern/trendline.py`, same primitive, shorter lookback) answering the
  "Trend is Up/Down" gate almost every pattern in the table requires.
- **`backend/app/services/pattern/pattern_utils.py`** gained
  `nearest_swing_target()` — "next major support/resistance" targets (used
  by several patterns) reuse `SwingDetector`; since a pattern detected at
  the most recent candle has no *future* swings yet (fractals need bars on
  both sides), this falls back to an ATR×3 projection — the natural stand-in
  for "next major level" before that level has actually formed.
- **Confirmation logic reuses `status_from_breakout()` uniformly** — every
  confirmable pattern's own high/low (or a specific rule-defined level, e.g.
  Three Line Strike's `C1.open`) becomes `breakout_level`; its stop becomes
  `invalidation_level`. DEVELOPING → CONFIRMED → BROKEN falls out of the
  exact same shared function every other pattern family already used — no
  special-cased "is this pattern already confirmed by its own last candle"
  branching needed, even for the patterns whose own table row says "C3/C4
  itself is the confirmation" (Star, Three Line Strike, Three Outside/Inside
  Up/Down) — their breakout_level is simply set at the exact price their own
  detection rule already required price to clear, so status reads CONFIRMED
  immediately and can still correctly flip to BROKEN later if price reverses
  hard against it.
- **Three detector files**, one per candle-count family (`BasePatternDetector`
  subclasses, registered in `PatternFactory`):
  - `single_candle_patterns.py` — Marubozu, Standard/Dragonfly/Gravestone
    Doji, Hammer, Hanging Man, Inverted Hammer, Shooting Star, Spinning Top,
    Inside Bar (10 patterns; Inside Bar needs one prior "mother" candle).
    Standard Doji, Spinning Top, and Inside Bar are genuinely
    direction-**neutral** by definition — which way they resolve depends on
    a breakout that hasn't happened yet at detection time. These are
    reported as `direction=NEUTRAL`, `status=DEVELOPING` always, with
    `stop_loss`/`target_1` left `None` and both the range-high and range-low
    shown as chart levels instead of guessing a direction — the honest
    representation of "undecided," not a missing feature (verified via a
    dedicated synthetic test asserting exactly this).
  - `two_candle_patterns.py` — Bullish/Bearish Kicker, Bullish/Bearish
    Engulfing, Bullish/Bearish Harami, Piercing Line, Dark Cloud Cover,
    Tweezer Bottom/Top (10 patterns). Bearish Kicker and Three White
    Soldiers/Black Crows (below) use `no_fixed_target=True` — their own
    table row says "Trailing Stop until reversal," so `target_1` is
    correctly left `None` rather than inventing a number the source
    material explicitly says doesn't exist.
  - `three_candle_patterns.py` — Morning/Evening Star, Bullish/Bearish
    Abandoned Baby, Three White Soldiers/Black Crows, Bullish/Bearish Three
    Line Strike, Three Outside Up/Down, Three Inside Up/Down (12 patterns;
    Three Line Strike needs a 4th candle — C1-C3 form the setup, C4 is the
    massive engulfing confirmation candle, both part of the same
    detection pass, not a later confirmation).
  - Every pattern's Entry/Stop/Target follows the reference table exactly,
    including its explicit R/R ratios where given (Hammer/Kicker 1:2,
    Harami/Three Inside/Three Outside 1:1.5) via a shared `rr_override`
    param, and its exact stated stop level even where asymmetric across a
    bull/bear pair (e.g. Bearish Kicker's confirmation is against `C2.low`
    while Bullish Kicker's is against `C1.high` — matched literally, not
    "symmetrized" for tidiness).
- **New config block**: `pattern_config.py` gained `CANDLESTICK_*` (wick/body
  ratio thresholds, midpoint threshold, equal-level tolerance, gap/volume
  multipliers, star body max, soldier/crow min ATR multiple, trend-context
  lookback+tolerance, default R/R) — all sourced directly from the user's
  table's "Detection Parameters" column, no hardcoded literals in the
  detector files themselves. The old chart-shape-only config constants
  (`DT_*`, `HS_*`, `TRIANGLE_*`, `WEDGE_*`, `FLAGPOLE_*`/`FLAG_*`,
  `CHANNEL_*`, `CUP_*`/`HANDLE_*`, `BROADENING_*`/`DIAMOND_*`) were removed
  as dead config alongside their detector files. `FVG_*`/`SMC_*`/`OB_*`/
  `LIQUIDITY_*`/`BOS_*`/`PATTERN_SCAN_*`/`CONF_WEIGHT_*` etc. are untouched
  — still shared/used.
  `CANDLESTICK_LOOKBACK_BARS = 150` — deliberately much shorter than the old
  chart-shape lookbacks (300-1000 bars): candlestick patterns are short-term
  signals, a Hammer from 800 candles back isn't a meaningful "detection"
  today the way an old Double Top's neckline level still can be.
- **Frontend fix required for the chart to actually satisfy the ask**
  ("when a person sees this pattern on the chart, they should know what
  pattern it is"): `PatternAnalysis.tsx`'s annotation-drawing effect
  previously only drew a pattern's text `labels` for the currently
  **selected** pattern — fine for the old chart-shape patterns (a
  non-selected one still showed its trendline/zone), but a candlestick
  pattern has no trendline/zone at all, just a single point in time, so a
  non-selected candlestick pattern was completely invisible on the chart.
  Moved `a.labels.forEach(...)` outside the `isSelected` guard — every
  visible pattern now always gets its name-labeled marker; only the full
  price-line read-out (breakout/invalidation/SL/targets) stays
  selected-only, to avoid burying the chart under overlapping horizontal
  lines when many patterns are visible at once.
- **Tests**: `tests/test_candlestick_patterns.py` (NEW) — factory
  registration (old detector keys gone), synthetic positive-path checks for
  a representative sample across all three files (Marubozu, Standard Doji
  neutral-with-no-stop, Dragonfly Doji, Hammer 1:2 R/R, Bullish Engulfing,
  Piercing Line, Tweezer Bottom, Morning Star, Three White Soldiers
  no-fixed-target, Three Inside Up 1:1.5 R/R), plus a live-data run across
  all 4 registered detectors and a full `PatternScanner.scan()` call.
  `tests/test_pattern_scanner.py` needed no logic changes — it already
  iterated `PatternFactory.list_detectors()` generically, so it transparently
  now exercises the candlestick detectors instead. It DID need one scope
  fix: its `include_ai=True` assertion ran at `limit=300` (the same window
  as the main scan test), which under the candlestick engine now finds
  ~129 patterns instead of the old ~30-54 — that single assertion measured
  at **4:42 wall-clock** (5.7s CPU / rest pure NVIDIA API latency across
  ~129 sequential-batch AI calls), which blew through the 180s-per-file
  timeout used when running the full test suite and made that one run
  register as "failed" even though every individual check inside it passed.
  Not a functional bug — `include_ai=True`'s cost scaling with pattern count
  is already documented, accepted behavior (see the Pattern Recognition
  timeout-fix section above) — just a test that needed a smaller window
  (`limit=60`, ~37 patterns) to stay within a reasonable single-test budget
  while still verifying the same thing (AI attaches to every pattern found).
- **Real volume difference found while verifying, not a bug but worth
  recording**: a single live scan (BTCUSDT/1h/300 candles) now returns
  ~128 patterns total (50 single + 53 two + 16 three + 12 SMC) vs. the old
  chart-shape engine's typical 11-31 — expected and correct, not a
  regression: candlestick patterns are inherently far more frequent than
  multi-week chart shapes, and this is standard behavior for any real
  candlestick-pattern scanner (professional platforms show similar
  density). Confirmed the existing rate-limit/timeout safeguards built for
  the old pattern module (opt-in `include_ai`, shared AI thread pool,
  `AI_REQUEST_TIMEOUT_SECONDS`) already absorb this fine — full scan still
  completed in ~1.7s (fast path) and the `include_ai=True` path still
  completed successfully in testing, not re-triggering the earlier
  "scan failing most of the time" timeout issue.
- Deleted: the 8 old detector files + their now-dead config constants. No
  test files referenced them by name (they were verified ad-hoc during
  their own build, per this doc's own earlier notes), so nothing else
  needed cleanup. No frontend code referenced old `pattern_type` strings
  either (`pattern_name`/`pattern_type` are rendered generically everywhere)
  — the only hit for old pattern names anywhere in the frontend was an
  unrelated prose analogy in the Trend Line tool's help text ("similar to a
  rising/falling wedge"), left alone.

### Candlestick pattern engine — full audit (2026-07-04, same day)

User reported the new candlestick engine was producing many incorrect
signals and asked for a full pattern-by-pattern audit: every one of the 32
patterns checked individually against its official rules, dedicated pos/
neg/edge tests per pattern, live backtest, before moving to the next.
Done in 3 batches (single/two/three-candle), one at a time, per instruction.

**7 root-cause bugs found, touching 15 of 32 patterns** (mirror pairs share
one root cause):

1. **Hammer/Hanging Man/Inverted Hammer/Shooting Star** — the "opposite
   wick stays small" check used an ad-hoc `max(body, dominant_wick×0.3)`
   formula; when body was large this became too permissive, accepting
   candles with a visually significant opposite wick. Fixed: unified
   `opposite_wick ≤ dominant_wick × CANDLESTICK_OPPOSITE_WICK_MAX_RATIO`
   (new config constant, 0.3), applied identically to all 4 shapes.
2. **Inside Bar** — two bugs: (a) built its `DetectedPattern` off the
   *mother* candle instead of the current (baby) candle, so
   `formation_end`/`current_price`/the chart label all landed one bar too
   early with a stale price; (b) architecturally shadowed by the
   single-candle shape checks ahead of it in the detection loop (Inside Bar
   is a candle-*pair* relationship, not a shape of the current candle, so
   "first match wins" incorrectly prevented it from ever firing whenever
   the baby candle also had its own shape — a very common case). Fixed:
   pass the baby candle to the builder; restructured the loop so Inside Bar
   always runs independently.
3. **Bullish/Bearish Engulfing** — missing explicit `C1 bearish AND C2
   bullish` (or mirror) check. Body-overlap inequalities alone don't force
   the right colors — two same-colored small candles sitting inside a
   larger one could satisfy the math without being a real engulfing
   pattern. Fixed: added the explicit color guard. Live BTCUSDT/1h/500
   effect: bullish_engulfing count dropped from ~14 to 1–4.
4. **Morning/Evening Star** — missing "C3 gaps up/down from C2," a
   detection condition explicitly separate from the confirmation condition
   in the source spec ("C3 closes strong into C1's body" ≠ "C3 gaps up").
   Only the confirmation half had been implemented. Fixed: added the gap
   check.
5. **Bullish/Bearish Abandoned Baby** — could never actually fire. It's a
   strictly rarer/stricter variant of Star (Doji middle + full gaps both
   sides), so any genuine Abandoned Baby also satisfies Star's looser gap
   rule — and Star was checked first, so it always won. Same "specific
   pattern must be checked before the general one" rule already correctly
   applied to Doji-before-Hammer in the single-candle detector, just missed
   here. Fixed: reordered the three-candle check list.
6. **Three White Soldiers/Black Crows** — missing "each candle opens within
   the prior candle's real body." Without it, 3 same-colored candles that
   merely closed progressively higher/lower while gapping wildly apart (a
   parabolic run, not a genuine grinding advance) still qualified. Fixed:
   new shared `opens_within_body()` helper in `candlestick_utils.py`.
7. **Three Outside Up/Down** — same missing-color-check bug as #3; this
   pattern's C1/C2 sub-shape duplicates the Engulfing overlap math but
   hadn't independently received the earlier fix. Fixed: same color guard
   added here too.

**17 of 32 patterns verified correct with no changes** — including cases
that could easily be mistaken for bugs but aren't: Bearish Kicker's
breakout level is `C2.low` (not `C1.low` like the bullish side) and
Harami/Tweezer correctly do NOT require certain color checks that
Engulfing does — both match the source spec's literal, intentionally
asymmetric wording.

**New test files** (dedicated per-pattern pos/neg/edge suites, one per
batch, 63 checks total, all passing): `tests/test_candlestick_single_candle_audit.py`,
`tests/test_candlestick_two_candle_audit.py`, `tests/test_candlestick_three_candle_audit.py`.
Existing `tests/test_candlestick_patterns.py` needed its Three White
Soldiers synthetic candle updated (it gapped between candles — exactly the
bug fix #6 now correctly rejects).

**Refactor pass** (after all 32 verified): extracted `opens_within_body()`
as a shared helper instead of duplicating it; removed dead
`gapped_up`/`gapped_down` imports from `three_candle_patterns.py` (unused
since the file's original build); confirmed zero unused imports remain
across all 4 candlestick files via AST analysis.

**Final verification**: all 63 new audit tests pass, full 47-file backend
regression suite passes, live backtest on BTCUSDT/1h/500 candles (125
patterns, 0 malformed, several spot-checked by hand against raw OHLC),
live `GET /patterns/scan` endpoint verified after a backend restart (the
usual gotcha — code changes need a manual uvicorn restart).

### Frontend restructure — Paper Trading form, Pattern Dashboard redesign, symbol search, Signals→Retail Dashboard merge (2026-07-04, same day)

Four requests, all frontend-only — `GET /market/symbols` already existed
and was fully wired backend-side (`binance_provider.py:get_symbols()` →
`market_service.py` → the endpoint), just never called from the frontend.

- **Paper Trading manual entry**: `PaperTrade.tsx` had no Entry/Stop Loss/
  Target form at all — placing a manual order only ever happened via the
  "Place Paper Trade" button on a `SignalCard`. Added a "Manual Trade Entry"
  card (Symbol/Direction/Entry/Stop Loss/Target/Risk %) with a live-computed
  R/R ratio (`calcRR()` — risk = |entry−stop|, reward = |target−entry|,
  direction-agnostic) shown as you type, submitting via the existing
  `POST /paper/order` (no backend change needed — `risk_percent` was
  already an optional field, just never exposed in this UI). Also added
  live P&L % to the existing open/closed manual-orders tables
  (`pnlPercent()` — generic `pnl / (entry × quantity) × 100`, works for
  both BUY/SELL since the backend already returns a correctly-signed pnl;
  no backend field needed, purely derived client-side from fields already
  returned).
- **Pattern Dashboard redesign**: split into Bullish/Bearish sections
  (`PatternSection` component), each sorted by timeframe using a fixed
  chronological order (`INTERVAL_ORDER`, not alphabetical — `1m` before
  `1d`). Removed the Price/Entry/Stop Loss/Target/R:R/Updated columns,
  leaving just Timeframe/Pattern/Confidence. Filtered to `status ===
  'CONFIRMED'` only. NEUTRAL-direction patterns (Doji, Spinning Top, Inside
  Bar) never reach CONFIRMED by design (see the candlestick audit above),
  so they drop out of this view automatically — no extra handling needed.
- **Symbol search everywhere**: new `SymbolSearchInput` component
  (`frontend/src/components/`) — fetches all ~1,300 tradeable symbols once
  (module-level cache, shared across every screen instance) via the
  now-consumed `GET /market/symbols`, filters client-side as you type,
  dropdown with keyboard nav (arrows/Enter/Escape). Wired into Dashboard
  (previously a **hardcoded `SYMBOL` module constant with no state at
  all** — converted to real `usePersistedState`, all its effects/chart
  re-run on symbol change), Backtest, Paper Trade (both the auto-bot config
  and the new manual-entry form), Pattern Dashboard, and Retail Dashboard.
- **Signals merged into Retail Dashboard**: `Signals.tsx` deleted; its
  Market Scan + Multi-Timeframe scan + `SignalCard` detail logic extracted
  into `frontend/src/components/SignalsSection.tsx`, which takes the
  parent's `symbol` as a prop (shared, not duplicated state) but keeps its
  own strategy/interval selection internally. Embedded into
  `PatternAnalysis.tsx` directly below the Analysis Tools card (same left
  column, above the fold — not full-width, since that column is already
  the wide one). Page renamed "Pattern Analysis" → "Retail Dashboard"
  (`PatternAnalysis.tsx`'s H1, kept the same `/patterns` route to avoid
  breaking existing links/bookmarks — only the nav label and on-page title
  changed). Sidebar's standalone "Signals" entry removed, `/signals` route
  deleted from `App.tsx`.
- Verified live via headless-Chrome: sidebar nav correct (no Signals entry,
  "Retail Dashboard" label), Retail Dashboard renders with the embedded
  Signals section, Pattern Dashboard shows Bullish(58)/Bearish(62) sections
  with only Timeframe/Pattern/Confidence columns, Paper Trade's live RR
  showed exactly `1:2.00` for entry=100/stop=95/target=110 (risk=5,
  reward=10 — correct), symbol search returned real matches (`ETHBTC`,
  `ETHUSDT`, etc.) for query "ETH". Frontend `tsc --noEmit` clean
  throughout. No backend changes were needed for any of this.

---

## Immediate Next Task

**Phase 3 — Advanced Risk Management**
Start with: `backend/app/services/position/kelly_position.py` (Kelly Criterion position sizing)
Then: `backend/app/services/risk/drawdown_guard.py` (drawdown protection)
Then: `backend/app/services/risk/daily_loss_limit.py` (daily loss limit)

---

## File Naming Conventions

```
backend/app/services/<domain>/base_<domain>.py      — abstract base
backend/app/services/<domain>/simple_<domain>.py    — default implementation
backend/app/services/<domain>/<domain>_factory.py   — factory
backend/app/schemas/<domain>.py                     — pydantic schemas
backend/app/api/v1/<domain>.py                      — FastAPI router
tests/test_<domain>_service.py                      — test
```

---

## Docs Location

`/media/sun/drive/devops-project/trading app/AI-Trading-Platform/AI-Trading-Platform/docs/`

Key docs:
- 00_PROJECT_OVERVIEW.md
- 01_ARCHITECTURE.md
- 03_ROADMAP.md
- 04_CURRENT_WORK.md
- 07_NEXT_TASKS.md
- 09_STRATEGY_ENGINE.md
- 13_TRADING_ENGINE.md
- 15_RISK_MANAGEMENT.md

---

## Environment Variables Required

```
KRONOS_PATH       # local path to Kronos model
DEFAULT_SYMBOL    # e.g. BTCUSDT
DEFAULT_INTERVAL  # e.g. 5m
DEFAULT_LOOKBACK  # integer
DEFAULT_PRED_LEN  # integer
```

NEVER commit: BINANCE_API_KEY, BINANCE_SECRET, OPENAI_API_KEY, CLAUDE_API_KEY,
              DATABASE_URL, JWT_SECRET

---

## Running Tests

```bash
cd "/media/sun/drive/devops-project/trading app/AI-Trading-Platform"
PYTHONPATH=. .venv/bin/python tests/test_<name>.py
```

---

## Running the Project

`./run.sh` from the project root — starts backend (:8000) + frontend (:5173)
together, health-checks the backend, logs to `logs/`, Ctrl+C stops both.
Requires `.env` (copy from `.env.example`), `.venv` set up, and
`frontend/node_modules` installed — the script checks for all three and
tells you what's missing rather than failing silently.

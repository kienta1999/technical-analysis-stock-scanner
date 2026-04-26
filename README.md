# technical-analysis-stock-scanner

Long-only, rules-based swing-trading strategy for the top 100 S&P 500 stocks by market cap. Designed to be run through Claude Code — the `/technical-analysis` slash command executes the scanner and interprets the output.

Backtested 2024-04-20 → 2026-04-20 (2 years):

```
$10,000 → $27,242   (+172.4%)
SPY B&H: +45.6%
Alpha:   +126.9 pp   [BEAT ✓]
42 trades, 22W / 20L, 52% win rate
```

Out-of-sample regime sweep (all tuned on 2024-2026, run with regime gate live):

- **2008 GFC full cycle** (2007-10-10 → 2009-12-31): +30.2% vs SPY -24.1% → **+54.4pp alpha**, gate blocked 337 days
- **2020 COVID crash** (2020-02-19 → 2020-12-31): +42.4% vs SPY +12.0% → **+30.4pp alpha**, 60% win rate
- **2022 bear + 2023 recovery** (2022-01-01 → 2024-01-01): +19.1% vs SPY +2.6% → **+16.4pp alpha**, gate blocked 187 days
- **2018 vol shock** (2018-01-01 → 2019-01-01): +1.0% vs SPY -5.2% → **+6.3pp alpha**, gate blocked 15 days (Feb VIX, Q4 selloff)
- **2015 chop** (2015-01-01 → 2016-01-01): **-12.9% vs SPY +1.3% → -14.2pp alpha [LOST ✗]**, 2W/12L, gate only blocked 46 days

The crisis windows (GFC, COVID, 2022 bear, 2018 shock) all clear because the regime gate kicks in. **2015 is the failure mode**: a textbook flat/chop year where SPY stayed above its 200DMA all year, the gate barely engaged, and every trend setup whipsawed. The strategy needs a trend; it has no defense against a year-long sideways grind.

---

## The full rulebook

### 1. Universe

- Top 100 S&P 500 companies by market cap, re-queried from Wikipedia + yfinance, cached locally in `data/universe_top100.csv`.
- Refreshed automatically if the cache is older than 7 days, or on demand with `--refresh`.

### 2. Direction rule (the one that makes everything work)

**Per-ticker filter:**

- **price > SMA200 → consider LONG setups only.**
- **price < SMA200 → no trade.** Never short, never fight the dominant trend.

**Market-wide regime gate (added 2026-04-23):** even for tickers above their own SMA200, block LONG entries when either:

- **SPY close < SPY 200-day MA** (broad market not in uptrend), OR
- **VIX ≥ 30** (crash regime — don't catch falling knives)

Lives in `scripts/signals.py` as `long_regime_ok()` — single SOT, applied by the shared `simulate()` engine used by both the backtest and tuner. Swung COVID-2020 alpha from **-24.9pp → +30.4pp** (see "Regime gate" section below). Do not "all in on the cross" in a bear regime — breadth <30% = prefer cash over forced longs.

### 3. Relative-strength filter (added 2026-04-25)

Even on a regime-OK day, only allow entries on tickers in the **top 40% of the universe by both 3-month and 6-month return** (intersection). Drops about 60% of names before setup evaluation. Goal: stop buying former winners that are already rolling over — exactly the failure mode that destroyed the strategy in 2015 chop.

Lives in `scripts/signals.py` as `rs_eligible()`, applied by the shared `simulate()` engine and the live scanner. Configurable via `RS_*` constants. Flipped 2015 chop alpha from **-14.2pp → +14.3pp** and improved 5 of 6 OOS windows; aggregate +74.7pp across the regime sweep. See "Tuning session round 6" section below for the eight-iteration sweep that landed on these knobs.

### 4. The four long setups

All setups require a **green candle** AND **volume > 20-day volume MA** on the trigger bar. If volume is weak, skip and wait.

| #   | Setup            | Key conditions                                                                                 | SL           | TP         |
| --- | ---------------- | ---------------------------------------------------------------------------------------------- | ------------ | ---------- |
| L1  | Ride Uptrend     | SMA50 > SMA200, price ≥3/5d above BB mid, RSI > 50, recent pullback to SMA50                   | **2× ATR**   | **4× ATR** |
| L2  | MACD Cross       | MACD histogram just crossed zero up, RSI 50–70, price > SMA50 but not touching upper BB        | **2.5× ATR** | **5× ATR** |
| L3  | VWAP Support     | SMA50 > SMA200, price 0–1.5% above VWAP (dipping toward it as support), RSI > 45               | **2× ATR**   | **3× ATR** |
| L4  | Pre-Golden Cross | SMA50 approaching SMA200 from below (<2% gap), price already > SMA200, RSI > 45, vol > 1.2× MA | **2× ATR**   | **4× ATR** |

### 5. Volatility guardrail

**Skip any entry where ATR% > 4.0.** Extreme-vol names (high-beta tech on news days, etc.) blow through wide stops before the setup works. Enforced by both the live scanner and the backtest.

### 6. Trade management — this is where most of the alpha comes from

1. **Initial stop** at the SL shown in the table (2× or 2.5× ATR below entry).
2. **Trailing-to-breakeven**: once price travels **50% of the way from entry to TP**, raise SL to entry. One-way ratchet — SL only moves up, never down, and only once.
    - Worked example: entry $130.52, TP $144.48. Midpoint = $137.50. When price tags $137.50, SL moves from $123.54 → $130.52. From then on, worst case is $0, best case is still +10.7%.
    - This rule alone converts several would-be losers into $0 scratches (AVGO, NEE ×2 in the 2-year backtest).
3. **Time stop**: exit at the close after **40 trading days** if neither TP nor SL has been hit — free up capital for fresh setups.
4. **One trade at a time.** Only scan for a new setup after the current trade exits. If the best setup on a given day scores below quality threshold (25), sit on hands.

### 7. Setup quality score (0–100)

Defined in `scripts/signals.py` (`quality()`). Used by **both** the backtest (picks the highest-scoring trigger each day) and the live scanner (surfaced as a `Quality` column to help rank when multiple setups trigger).

| Factor            | Max pts | Full credit                  | Half credit              |
| ----------------- | ------- | ---------------------------- | ------------------------ |
| Volume conviction | 35      | vol_ratio ≥ 2.0× MA (linear) | 1.5× = 17 pts            |
| RSI sweet spot    | 30      | 55–65 for longs              | 50–70 for longs (15 pts) |
| ATR Goldilocks    | 20      | 1.5–3.5%                     | 1.0–5.0% (10 pts)        |
| Trend alignment   | 10      | LONG + SMA50 > SMA200        | —                        |
| MACD alignment    | 5       | LONG + macd_hist > 0         | —                        |

`MIN_QUALITY_SCORE = 25` is the floor — below this the backtest sits in cash and the operator should skip the trade.

Score buckets to keep in mind:

- **80–100**: premium setup (BA's Pre-Golden Cross today scores 90 with 2.4× volume)
- **60–79**: workable but watch the weak factor (usually volume)
- **40–59**: marginal — skip unless multiple setups confirm same ticker
- **<40**: weak — backtest skips automatically below 25

### 8. Indicators computed per ticker

- SMA 50, SMA 200 (trend direction)
- Bollinger Bands (20, 2σ): upper / mid / lower
- RSI (14, EWM)
- ATR (14, EWM) — drives SL/TP sizing
- MACD (12, 26, 9): line, signal, histogram
- Volume + 20-day volume MA + vol ratio
- Rolling VWAP (20-day proxy)

---

## How to use it

### Run the scanner (live)

```bash
.venv/bin/python3 scripts/sma200_filter.py
```

Or in Claude Code: `/technical-analysis`.

Output: market-breadth regime, LONG universe table, and any triggered setups with **Quality (0–100)**, exact Entry / SL / TP / breakeven-trigger prices. Setups are sorted by Quality descending.

### Run the backtest

```bash
.venv/bin/python3 scripts/backtest.py
```

Configurable at the top of `scripts/backtest.py`:

```python
START_DATE        = date(2024, 4, 20)   # 2-year window by default
END_DATE          = date(2026, 4, 20)
CAPITAL_INIT      = 10_000.0
TIME_STOP_DAYS    = 40
BENCHMARK         = "SPY"
```

All algo-level knobs — setup thresholds, SL/TP ATR multipliers, quality-score weights, `MIN_QUALITY_SCORE`, AND the pre-setup global filters — live in `scripts/signals.py` as the single SOT, imported by both the backtest engine and the live scanner. Top of the file:

```python
# Algo-level filters (applied before any setup is evaluated)
MAX_ATR_PCT    = 4.0    # skip entries where ATR% > this (vol-cap guardrail)
SPY_MA_PERIOD  = 200    # SPY trend filter for long-entry regime gate
VIX_MAX        = 30.0   # block LONG entries when VIX >= this

# Plus L1/L2/L3/L4 setup thresholds, quality-score weights,
# MIN_QUALITY_SCORE, market_regime(), long_regime_ok() ...
```

Edit there and re-run the backtest to A/B a change.

The core simulation loop (`simulate()`) lives in `scripts/backtest.py` and is imported by `scripts/tune.py` — parameter sweeps inherit every rule change automatically, zero drift between backtest and tuner.

### First-time setup

```bash
uv venv .venv -q
uv pip install yfinance pandas lxml requests --python .venv/bin/python3 -q
```

---

## Live paper trading — daily on GitHub Actions

`.github/workflows/daily-scan.yml` runs the strategy in paper mode every US trading day. **No real money — pure simulation, persisted to git.**

### What runs each day

| Step              | Command                                                                | Output                              |
| ----------------- | ---------------------------------------------------------------------- | ----------------------------------- |
| Resolve run flag  | bash gate (skip weekends, skip non-9 ET hour, allow `workflow_dispatch`) | `gate.outputs.date`                 |
| Run scanner       | `python sma200_filter.py > scans/<date>.txt`                           | committed scan report               |
| Run paper trade   | `python paper_trade.py --date <date>`                                  | updates `logs/paper_state.json`, appends to `logs/paper_trades.csv` and `logs/paper_portfolio.csv` |
| Commit output     | `git add scans/ logs/ && git commit -m "scan + paper: <date>" && git push` | one commit per trading day          |

Two cron entries (`13:30` and `14:30` UTC) cover both DST states; the gate step ensures only the one matching 9:00 ET actually runs. Manual re-runs via `workflow_dispatch` accept an optional `date` override.

### Log files — what each one means

#### `logs/paper_state.json` — single source of truth
Live snapshot consumed by the next run. Overwritten in-place each day (atomic `.tmp` → rename); git history preserves every prior version.

```json
{
  "starting_capital": 10000.0,
  "starting_date":    "2026-04-27",
  "max_slots":        1,
  "slots": [
    {
      "idx":      0,
      "cash":     0.0,                  // free cash in this slot
      "position": {                      // null when slot is empty
        "ticker": "AAPL", "direction": "LONG",
        "setup":  "Ride Uptrend", "quality": 75.0,
        "entry_date":          "2026-04-27",
        "scan_date":           "2026-04-24",
        "entry":               175.50, "shares": 56.98,
        "sl":                  170.00, "original_sl": 170.00,
        "tp":                  195.50, "be_trigger":  185.50,
        "be_moved":            false,
        "days_held":           3,
        "last_processed_date": "2026-04-29"
      }
    }
  ],
  "last_run_date": "2026-04-29"
}
```

If you ever delete or edit the CSV logs, this is the file the next run reads — the simulation continues correctly.

#### `logs/paper_trades.csv` — append-only trade journal
One row per *event*. Action types:

| Action       | Meaning                                                                  |
| ------------ | ------------------------------------------------------------------------ |
| `BUY`        | Slot opened a position. Records entry price, shares, SL, TP, BE-trigger. |
| `BE_MOVE`    | Trailing-to-breakeven fired — SL raised to entry. Position still open.   |
| `SELL_SL`    | Stop-loss hit (intraday low ≤ SL). Position closed, slot cash refilled.  |
| `SELL_TP`    | Take-profit hit (intraday high ≥ TP). Position closed.                   |
| `SELL_TIME`  | 40-day time stop — exited at the bar's close.                            |

Columns: `run_date, scan_date, action, slot, ticker, setup, quality, price, shares, sl, tp, be_trigger, pnl_pct, pnl_usd, slot_cash_after, portfolio_value, days_held, note`. `pnl_*` are blank for `BUY` / `BE_MOVE`.

#### `logs/paper_portfolio.csv` — append-only daily mark-to-market
One row per workflow run. Columns:

| Column                                                | Meaning                                                            |
| ----------------------------------------------------- | ------------------------------------------------------------------ |
| `run_date`                                            | Workflow run date (NY).                                            |
| `scan_date`                                           | Date of the latest OHLCV bar the scan saw (usually `run_date − 1`). |
| `cash`                                                | Sum of free cash across all slots.                                 |
| `positions_value`                                     | Sum of `shares × latest_close` for every open position.            |
| `total_value`                                         | `cash + positions_value` — equity curve datapoint.                 |
| `return_pct`                                          | `(total_value / starting_capital − 1) × 100`.                      |
| `open_count`, `open_tickers`                          | How many slots are deployed and into what.                         |
| `gate_open`, `spy_price`, `spy_ma`, `vix`             | Regime snapshot.                                                   |
| `scan_picks_count`, `top_pick`                        | What the scanner found that day.                                   |

Use this CSV to chart the equity curve vs SPY without replaying any trades.

### Resetting the simulation

To restart from a fresh $10k:

```bash
rm -f logs/paper_state.json logs/paper_trades.csv logs/paper_portfolio.csv
git add logs/ && git commit -m "paper: reset" && git push
```

Next workflow run will re-init `starting_capital = 10_000` and `starting_date = <today>`.

---

## Code layout — what each file does

```
scripts/
  universe.py       — top-100 S&P 500 universe loader
  indicators.py     — per-ticker indicator math
  signals.py        — SOT for every algo-level rule and tunable
  sma200_filter.py  — live EOD scanner (CLI + scan() API)
  backtest.py       — simulate() engine + 2-year backtest CLI
  tune.py           — parameter grid search with IS/OOS split
  run_oos.py        — six-window historical regime sweep
  paper_trade.py    — daily paper-trade simulator (driven by GitHub Actions)
data/               — cached OHLCV pickles + universe CSV (gitignored)
scans/              — committed daily scan output (one .txt per trading day)
logs/               — committed paper-trade state + trade/portfolio history
.github/
  workflows/
    daily-scan.yml  — 9:30 AM ET workflow: scan → paper_trade → commit
.claude/
  commands/         — slash commands for Claude Code
  settings.json     — project default model
```

### `scripts/universe.py`
Fetches the **top 100 S&P 500 companies by market cap** from Wikipedia + yfinance, caches to `data/universe_top100.csv`, refreshes if older than 7 days. Every other script reads its ticker list from `load_universe()`.

### `scripts/indicators.py`
Pure numerical: given a ticker's daily OHLCV frame, computes SMA-50/200, Bollinger Bands, RSI(14), ATR(14), MACD(12/26/9), volume ratio, rolling VWAP, and derived booleans (`price_above_sma200`, `macd_crossed_up`, `near_sma50_recently`, etc.). Returns a flat dict consumed by both the scanner and the backtest. No I/O, no rule logic — just math.

### `scripts/signals.py`
**The single source of truth for every trade rule.** All other scripts import their rules from here. Three things live here:
1. **Tunable constants** — `MAX_ATR_PCT`, `SPY_MA_PERIOD`, `VIX_MAX`, `MAX_SLOTS`, `MIN_QUALITY_SCORE`, `RS_*` (relative-strength filter knobs), `L1_*` … `L4_*` (per-setup thresholds), `Q_*` (quality-score weights).
2. **Setup detection** — `score(ind)` returns the list of L1/L2/L3/L4 setups triggered by a ticker's indicator dict on a given day. `quality(row)` scores any triggered setup 0–100.
3. **Algo-level gates** — `long_regime_ok()` (SPY>200DMA AND VIX<30), `rs_eligible()` (top 40% of universe by both 3M and 6M return), `market_regime()` (breadth label), `build_regime_series()` (precomputes SPY/VIX series for the backtest).

If you want to change the strategy, you change a constant or a function here. Nothing else.

### `scripts/sma200_filter.py`
**Live EOD scanner.** Run it after market close to see what the rulebook is saying right now. Downloads 1 year of OHLCV for the universe + SPY + ^VIX, computes indicators, prints:
- Market breadth (how many tickers above SMA200)
- Regime gate status (open / blocked + the SPY/VIX numbers driving it)
- RS filter status (how many tickers passed the top-40% cut)
- Long universe and short universe tables
- Triggered setups, sorted by quality, with full per-setup detail

`python3 scripts/sma200_filter.py` — no args. `--refresh` re-pulls the universe from Wikipedia.

Two entry points:
- **`scan(force_refresh=False, verbose=True) -> dict`** — programmatic API. Returns `{scan_date, gate_open, gate_detail, spy_price, spy_ma, vix, breadth_long, breadth_short, breadth_total, rs_eligible, long_rows, short_rows, triggered, picks, raw, tickers}`. `picks` is the actionable LONG candidate list (regime-allowed, ≥`MIN_QUALITY_SCORE`, sorted by quality desc), each entry containing `ticker, setup, direction, quality, entry, sl, tp, rsi, vol_ratio, atr_pct, rr`. `raw` is the full OHLCV frame so callers (`paper_trade.py`) can avoid re-downloading.
- **`run(force_refresh=False) -> dict`** — CLI wrapper: calls `scan()`, prints the human-readable report, returns the dict.

### `scripts/backtest.py`
**The reference simulator and CLI for a single date range.** Two pieces:
1. `simulate(raw, tickers, all_dates, bt_dates, ...)` — the core engine. Loops day by day: scan EOD, enter next-day open, monitor TP/SL/time-stop with daily highs/lows, track trailing-to-breakeven, score candidates, pick highest-quality, fill free slots. Used by `tune.py` and `run_oos.py` too.
2. CLI `run()` — defaults to 2024-04-20 → 2026-04-20, downloads OHLCV fresh, runs `simulate()`, prints trade log + benchmark comparison + alpha.

Editing `START_DATE`/`END_DATE` at the top runs the same engine on a different window. For multi-window evaluation use `run_oos.py` instead.

### `scripts/tune.py`
**Parameter grid search.** Defines a `GRID` dict (currently sweeping `MAX_SLOTS`), generates all variations, runs each through `simulate()` on both the in-sample window (2024-04-20 → 2025-04-20) and a held-out year (2025-04-20 → 2026-04-20), reports any variation that beats baseline by ≥10pp on **both** windows. OHLCV is cached to `data/raw_ohlcv_2y.pkl` (7-day TTL). The lesson from previous rounds: tune.py is reliable for **direction** of an effect but unreliable for predicting continuous-backtest **magnitude** — always re-validate any winner with `backtest.py`.

### `scripts/run_oos.py`
**Six-window OOS regime sweep — the verdict tool for any algo-level change.** Runs `simulate()` against each of: 2024-26 bull, 2015 chop, 2018 vol shock, 2020 COVID, 2022-24 bear+recov, 2008 GFC. Per-window OHLCV is cached to `data/raw_oos_<start>_<end>.pkl` (7-day TTL). Prints a Δ-vs-baseline table where the baselines are the alphas of the **currently shipped** config, and a ship rule (2015 alpha > 0 AND no window drops more than 10pp). Update the baseline column after any accepted change so future runs measure Δ vs the latest state of the art, not pre-change history.

This script replaced the previous workflow of editing `backtest.py`'s date range five times by hand. Use it before declaring any strategy change a win.

### `scripts/paper_trade.py`
**Daily paper-trade simulator.** Mirrors the algo's rules with $10k starting capital and `MAX_SLOTS` independent sub-account slots (currently 1 — same as the proven default). Run by GitHub Actions every weekday at 9:30 ET; can also be run locally as `python3 scripts/paper_trade.py --date YYYY-MM-DD`.

Per run:

1. Calls `sma200_filter.scan()` once — reuses the same OHLCV download for both scanning and position management (no duplicate yfinance calls).
2. Walks every open position through every bar > its `last_processed_date`. Per bar, applies in this order: trailing-to-breakeven (raise SL to entry once price hits 50% of the way to TP) → SL hit → TP hit → 40-day time stop. Identical to `backtest.simulate_trade`.
3. If a slot is free, regime gate is open, and the top-quality pick (≥`MIN_QUALITY_SCORE`) isn't already held → BUY at the scan's entry price (= last bar close). Slot's full cash converts to shares.
4. Mark-to-market all open positions using the latest close, append the day's row to `paper_portfolio.csv`.
5. Atomically write `paper_state.json`.

State of truth is `logs/paper_state.json` — committed by the workflow, so each daily run picks up where the last left off. The two CSVs are append-only history for human consumption.

---

## Why these specific rules — a short history

The first version of this strategy had **both long and short setups**, **1×/1.5× ATR stops**, and a **20-day time stop**. Over the 1-year window 2025-04-20 → 2026-04-20 it lost **-25.6% against SPY +39.8%** (alpha -65.4 pp). Four iterations fixed it:

| Change                                | Rationale                                                                       |
| ------------------------------------- | ------------------------------------------------------------------------------- |
| Disable SHORT setups                  | Shorts kept getting clipped by the dominant bull tape before any move developed |
| SL 2× ATR, TP 4× ATR (from 1× / 1.5×) | Tight stops get eaten by daily noise before the setup resolves                  |
| Time stop 20 → 40 days                | Winners like AVGO (+17.8% in 40 days) need room to run                          |
| Trailing-to-breakeven at 50% of TP    | Protects profits without capping upside — the single biggest alpha source       |

Result: flipped from losing -65 pp to beating +50 pp over 2 years.

Things that were tried and reverted (didn't help):

- Earlier BE trigger (40% of TP): scratches too many trades before they reach target
- Later BE trigger (60% of TP): more trades revert to full SL before lock

## Tuning session (2026-04-23) — L1 volume threshold raised to 1.3×

### What we did

Ran `scripts/tune.py` — 108-variation grid search across `MIN_QUALITY_SCORE`, `L1_SL_ATR`, `L1_TP_ATR`, `L1_MIN_VOL_RATIO`, `L4_TP_ATR`. Used proper train/test split: Year 1 (2024-04-20 → 2025-04-20) for tuning, Year 2 for held-out validation. A variation was only flagged as "robust" if it beat baseline by ≥10pp alpha on **both** windows.

### Headline finding

**24 of 108 variations cleared the bar — and every single one shares the same change: `L1_MIN_VOL_RATIO: 1.0 → 1.3`.** The other knobs (SL/TP/MQ) only mattered at the margins. One knob, one direction, validated across both years and many parameter combinations.

**Mechanism:** L1 (Ride Uptrend) was triggering on stocks with `vol_ratio` as low as 1.03 — barely above the 20-day average, essentially no real-money conviction. Quality scorer already weights volume heaviest (35 pts), but the trigger gate was letting marginal-volume names through. Raising the gate to 1.3× filters them out before they enter the candidate pool.

### Magnitude lesson — per-window tuning misled us

The tuner showed two attractive picks:

| Pick                                     | Y1 alpha (per-window) | Y2 alpha (per-window) |
| ---------------------------------------- | --------------------- | --------------------- |
| `L1_MIN_VOL_RATIO=1.3` + `L1_TP_ATR=5.0` | +24.4pp               | +21.8pp               |
| Just `L1_MIN_VOL_RATIO=1.3`              | +20–30pp              | +16–18pp              |

We tried the first pick first (volume + wider TP). Continuous backtest result: **-10.5pp alpha — LOST to SPY**.

Reverted to just the volume change. Continuous backtest: **+52.5pp alpha (vs baseline +50.1pp)**.

So the volume-only change is a real win, but only **+2.4pp better than baseline** — not the +20pp the tuner predicted. The wider TP actively _hurt_ in continuous mode (longer holds → more time-stop exits → fewer trades cycle through → less compounding) even though per-window analysis liked it.

### Lesson

**`tune.py`'s per-window-with-fresh-capital framework is useful for _ranking_ parameter directions but wildly unreliable for predicting _continuous_ P&L magnitude.** It's a screening tool, not a final verdict. Always re-validate any tuner finding by running the full continuous `backtest.py` before shipping.

### What's next

Today's tuning only varied L1 and L4 parameters (the most-triggered setups). L2 (MACD Cross) and L3 (VWAP Support) might have over-tight thresholds that block useful triggers — that's the next area to probe with another grid search round.

L2/L3 grid is wired up in `scripts/tune.py` (288 variations, ~4 hours overnight). Run with:

```bash
.venv/bin/python3 scripts/tune.py 2>&1 | tee /tmp/tune-l2l3.log
```

Output is saved to `/tmp/tune-l2l3.log` — read that file the next morning if the terminal session is gone. (Note: `/tmp` is wiped on reboot — copy somewhere durable if you don't analyze it the same day.)

## Tuning session round 2 (2026-04-23 overnight) — L2 volume threshold raised to 1.3×

### What we did

Ran the 288-variation L2/L3 grid overnight. Per-window analysis was inconclusive — only 4 variations cleared the +10pp/+10pp floor and they all _lost_ to the post-L1V1.3 baseline on Y1 (+30.7pp vs baseline +67.6pp) while winning Y2 (+16.3pp vs +7.1pp). Not a clean signal.

Tried the single most theoretically-motivated change anyway (`L2_MIN_VOL_RATIO: 1.0 → 1.3`, paralleling yesterday's L1 finding) and ran the continuous backtest.

### Continuous backtest result

| Metric         | L1V1.3 only | +L2V1.3     | Δ           |
| -------------- | ----------- | ----------- | ----------- |
| Return         | +98.1%      | **+121.8%** | **+23.7pp** |
| Alpha          | +52.5pp     | **+76.3pp** | **+23.8pp** |
| End cap ($10k) | $19,809     | **$22,183** | +$2,374     |
| Trades         | 30          | **41**      | +11         |
| Win rate       | 47%         | 46%         | ≈ same      |

### Why it worked — capital recycling, not setup selection

The L2 filter **didn't make L2 triggers better** — same 3 L2 trades (TJX/META/QCOM) in both runs. Instead, raising the L2 volume gate _kept the scanner from getting trapped in slow-grinder L2 entries that were blocking capital from faster-recycling L1/L3 opportunities_.

Concrete example: April 22 2024, baseline picks KO's MACD Cross (vol_ratio=1.2, quality 62.4) and holds 44 days for +5.9%. With the new gate, KO doesn't trigger → scanner picks GOOGL's VWAP Support instead → exits in 3 days at +5.8% → 41 freed days to compound through other trades.

Setup count shifted accordingly:

| Setup           | Before (30 trades) | After (41 trades) |
| --------------- | ------------------ | ----------------- |
| L1 Ride Uptrend | ~15                | ~20               |
| L3 VWAP Support | ~8                 | ~17               |
| L2 MACD Cross   | 3                  | 3                 |
| L4 Pre-Golden X | 1                  | 1                 |

### Methodological lesson — `tune.py` can be directionally wrong

**The `L2V1.3-only` combo was NOT in the grid's 4 qualifying variations.** Per-window analysis predicted it would fail the +10pp floor. Continuous mode showed it adds +24pp alpha. The per-window framework can't see capital-recycling effects because each year starts with fresh $10k and no carry-over state.

Previously we thought tune.py's output was just magnitude-unreliable. It's actually worse: **it can miss real winners entirely**. Treat tune.py as a candidate-generator only. Continuous backtest is the single source of truth.

### Current configuration

```
L1_MIN_VOL_RATIO = 1.3   (changed from 1.0 — tuning session 1)
L2_MIN_VOL_RATIO = 1.3   (changed from 1.0 — tuning session 2)
L3_SL_ATR        = 2.5   (changed from 2.0 — tuning session 3)
L3_TP_ATR        = 2.5   (changed from 3.0 — tuning session 3)
```

Sessions 1 & 2 fit one story: _volume conviction at the trigger gate matters as much as volume in the quality score_ (continuation setups L1/L2).

Session 3 fits the **opposite** story for L3 (mean-reversion): _bounces are short-lived; grab them quickly with a 1:1 R:R rather than waiting for full extension_. L3 win rate jumped from 53% to 69% with this change.

## Tuning session round 3 (2026-04-23) — L3 R:R tightened to 1:1

### What we did

Ran a 324-variation L3-only grid (5 dimensions: VWAP distance, RSI floor, BB-mid window, SL multiplier, TP multiplier — vol threshold deliberately excluded since round 2 proved it breaks L3). 17 of 324 cleared the +10pp/+10pp floor, in two clusters:

- **Cluster A (top 6)**: tighten L3 R:R to 1:1 — `L3_SL_ATR=2.5, L3_TP_ATR=2.5`
- **Cluster B (next 7)**: widen VWAP touch zone — `L3_VWAP_DIST_MAX=3.0`

### Continuous backtest result (Cluster A picked)

| Metric         | Pre-L3-tune | + L3 1:1 R:R     | Δ          |
| -------------- | ----------- | ---------------- | ---------- |
| Return         | +121.8%     | **+125.6%**      | **+3.8pp** |
| Alpha          | +76.3pp     | **+80.0pp**      | **+3.7pp** |
| End cap ($10k) | $22,183     | **$22,556**      | +$373      |
| Trades         | 41          | **44**           | +3         |
| Win rate       | 46%         | **48%**          | +2pp       |
| L3 win rate    | 53%         | **69%**          | +16pp      |
| L3 avg P&L     | +1.1%/trade | **+2.08%/trade** | +0.98pp    |

### Mechanism — opposite of L1

L1 wants wide TP (4× ATR) to let trending winners run. L3 wants tight TP (2.5× ATR) because VWAP bounces are short and quick — grab the move before it reverses. The wider SL (2.5× vs 2.0× ATR) also gives the trade more room to reach the trailing-BE trigger before chop noise stops it out.

### Per-window framework — 10× overestimate again

Tune.py predicted Y2 alpha would jump from -3.1pp to +33.2pp (+36pp Y2 improvement). Continuous reality was +3.7pp total alpha gain. Still directionally right, but the magnitude lesson keeps repeating: **always validate via continuous backtest before shipping**.

### Setup-by-setup stats in current config (41 trades, 2y)

| Setup               | Trades | Wins | Flat (BE) | Losses | Win rate\* | Avg P&L/trade |
| ------------------- | ------ | ---- | --------- | ------ | ---------- | ------------- |
| L1 Ride Uptrend     | 20     | 8    | 6         | 6      | 57%        | +2.4%         |
| L3 VWAP Support     | 17     | 8    | 2         | 7      | 53%        | +1.1%         |
| L2 MACD Cross       | 3      | 2    | 0         | 1      | 67%        | +6.0%         |
| L4 Pre-Golden Cross | 1      | 1\*  | 0         | 0      | —          | +1.8%         |

\*Win rate excludes BE-flat trades (trailing-to-breakeven saved a would-be loser). L4 exit was TIME-stop positive.

### Priority for future tuning rounds

1. **L3 VWAP Support** — highest frequency × lowest per-trade edge = biggest lever. Vol threshold already proven to hurt (mean-reversion setup; high vol on dips = distribution). Next dimensions: VWAP distance, RSI floor, SL/TP ratios.
2. **L1 Ride Uptrend** — biggest single contributor by total. Volume already tuned. Try RSI, BB-mid window, or pullback-proximity next.
3. **L2 MACD Cross** — best per-trade (+6.0%), only 3 triggers/2y. Last night's grid hinted `L2_RSI_MAX: 70→75` and `L2_TP_ATR: 5→6` might help — untested in continuous mode.
4. **L4 Pre-Golden Cross** — n=1, untouchable until universe broadens.

**Key methodological rule going forward:** always re-run `scripts/backtest.py` for continuous validation after ANY tune.py experiment. Per-window numbers can mislead in both magnitude and direction.

### Out-of-sample regime sweep (2026-04-25) — 2015, 2018, 2022-24 with regime gate live

Ran the post-tuning config (L1V1.3 + L2V1.3, current defaults, regime gate on) across three OOS windows that span a chop year, a vol shock, and a bear+recovery cycle. Tune window remains 2024-2026 only.

| Window                                | Result                                | Win rate | Gate-blocked days | Verdict      |
| ------------------------------------- | ------------------------------------- | -------- | ----------------- | ------------ |
| 2022-01-01 → 2024-01-01 (bear+recov)  | +19.1% vs SPY +2.6% → **+16.4pp**     | 42% (13/18) | 187            | **BEAT ✓**   |
| 2018-01-01 → 2019-01-01 (vol shock)   | +1.0% vs SPY -5.2% → **+6.3pp**       | 35% (8/15)  | 15             | **BEAT ✓**   |
| 2015-01-01 → 2016-01-01 (chop)        | -12.9% vs SPY +1.3% → **-14.2pp**     | 14% (2/12)  | 46             | **LOST ✗**   |

**2022-24 with gate vs without:** +16.4pp (gate-on) vs +16.2pp (gate-off, prior README number). The gate blocked 187 days but the resulting alpha is virtually identical — the 2022 bear had enough VIX>30 days that the structural protections (SMA200 + ATR vol cap) were already catching most of what the gate would block.

**2018 vol shock:** the gate fired during the Feb VIX spike and the Q4 selloff. Even with a 35% win rate the strategy turned a -5.2% SPY year into +1.0%. This is the gate's job — sit out the worst days, take what's left.

**2015 chop is the failure mode.** SPY ended +1.3% with no sustained trend in either direction; it stayed above its 200DMA almost all year, so the gate only engaged on 46 days. Every L1/L4 trend setup walked into noise — 14% win rate, 12 stops out of 14 trades. The regime gate is binary (trending up vs crash); it has no detection for "no trend at all." This is a real, structural cost of a long-only trend strategy and it should not be hand-waved.

## Regime gate (2026-04-23) — SPY>200DMA + VIX<30 for LONG entries

### The COVID-2020 stress test that broke the algo

Ran the fully-tuned config on 2020-02-19 → 2020-12-31 (COVID crash + recovery) and got demolished:

```
$10,000 → $8,713    (-12.9%)
SPY B&H: +12.0%
Alpha:   -24.9 pp    [LOST ✗]
17 trades, 6W / 11L, 35% win rate
```

Damage concentrated in two clusters:

1. **Feb 19-28 entries** (UNP/HD/NFLX): opened longs right as COVID broke, got stopped within days.
2. **Oct-Nov chop** (AMZN/PFE/META/PLD): pre-election volatility ate trend setups.

The algo _did_ partially adapt (no entries Mar 9 → Apr 29, skipping the worst of the crash) but the Feb losses and the post-election whipsaws were already baked in.

### The fix — a market-wide regime gate

Added `long_regime_ok()` in `scripts/signals.py` (single SOT, consumed by the shared `simulate()` engine). LONG entries now require BOTH:

- **SPY close > SPY 200-day MA** (broad trend intact)
- **VIX < 30** (no crash regime)

Either condition fails → the scanner won't trigger a LONG that day. Applied uniformly in `backtest.py` and `tune.py`.

### Results

| Window                                | Before gate                | After gate                 | Δ alpha     |
| ------------------------------------- | -------------------------- | -------------------------- | ----------- |
| COVID (2020-02-19 → 2020-12)          | -12.9% / alpha **-24.9pp** | +42.4% / alpha **+30.4pp** | **+55.3pp** |
| Bull run (2024-04-20 → 2026-04)       | +125.6% / **+80.0pp**      | +172.4% / **+126.9pp**     | **+46.9pp** |
| GFC full cycle (2007-10-10 → 2009-12) | —                          | +30.2% / **+54.4pp**       | —           |

- COVID window: gate blocked 68 days of LONG scanning. Trades dropped 17→15, win rate 35%→60%, alpha -24.9pp → **+30.4pp** ([BEAT ✓]).
- Bull window: gate blocked 45 days. Trades 44→42, win rate 48%→52%, alpha +80pp → **+126.9pp**.
- GFC full cycle: gate blocked **337 days** (56% of the window). 18 trades, 8W/10L, 44% win rate. The 2008 leg alone saved +52.7pp (strategy -1.8% vs SPY -54.6%); the 2009 recovery leg cost -26.8pp (strategy +32.7% vs SPY +59.5% — the same gate that blocked the crash also kept the scanner out of the sharpest V-recovery in market history). Net: **+54.4pp over the full peak-to-recovery cycle** — crash protection dominates recovery miss by 2×.

### Mechanism

The gate doesn't make individual setups better — it prevents entries during regimes where _all_ longs are structurally disadvantaged (volatility spikes and broad downtrends produce more whipsaws than signals). Sitting in cash during flagged regimes has higher expected value than forcing trades.

### Verdict

Combined with the L1/L2 volume tuning and L3 R:R tightening, the strategy now:

- **Beats SPY by +126.9pp** over the 2024-2026 tune window (up from +80pp pre-gate).
- **Beats SPY by +30.4pp** through the 2020 COVID crash (was losing -24.9pp pre-gate).
- **Beats SPY by +54.4pp** through the 2007-2009 GFC full cycle — an event that predates every parameter in the config.
- **Remains long-only** — no short-side exposure, just a cash-out during risk-off regimes.

The COVID and GFC results are strong evidence against in-sample fitting: neither 2020 nor 2008 was in the backtest until the gate was added, yet the same rules cleanly flipped two different disasters into outperformance. The edge is structural, not accidental.

**The honest tradeoff:** the 2009 sub-window (post-March low recovery) shows the gate's cost — the strategy returned +32.7% while SPY rebounded +59.5% off the crash low. Regime gates can't distinguish "bottom is in" from "bear rally." You're paying a late-entry tax on V-recoveries in exchange for not catching the falling knife on the way down. Over the full 2007-2009 cycle the crash protection wins by 2× — but if you're evaluating this strategy over a window that starts _at_ a crash low, it will look bad.

---

## Tuning session round 4 (2026-04-25) — concurrent slot count (MAX_SLOTS) — kept at 1

### Question

The single-trade backtest leaves capital idle most days. Would running 2–4 concurrent positions deploy that idle cash for higher returns, or would the diversification noise hurt? Added `MAX_SLOTS` to `signals.py` and refactored `backtest.simulate` so each slot is its own sub-account starting at `$10k / N` and compounding independently. Same-ticker dedup across slots; later signals fill empty slots first-come-first-served (no swap-on-better-quality).

### What we did

Ran a 4-variation `MAX_SLOTS ∈ {1, 2, 3, 4}` sweep on both windows (IS: 2024-04-20 → 2025-04-20, OOS: 2025-04-20 → 2026-04-20). The Baseline run uses the file default (also 1) and confirmed no state leakage — its alpha matched `SLOTS=1` exactly.

### Result

| Variation | IS alpha    | OOS alpha   | Sum                |
| --------- | ----------- | ----------- | ------------------ |
| Baseline  | **+53.8pp** | **+33.2pp** | **+87.0pp**        |
| SLOTS=1   | +53.8pp     | +33.2pp     | +87.0pp            |
| SLOTS=2   | +30.1pp     | +13.2pp     | +43.2pp            |
| SLOTS=3   | —           | —           | failed +10pp floor |
| SLOTS=4   | —           | —           | failed +10pp floor |

Each additional slot cut alpha roughly in half. SLOTS=3 and SLOTS=4 were so degraded they didn't clear the +10pp floor on at least one window.

### Why more slots hurt

The scanner's edge is concentrated in the **top-quality signal of the day**, not spread evenly across all triggers. Slots 2–N are forced to take the 2nd/3rd/4th-best candidates, whose quality scores are meaningfully lower. We're effectively paying to ignore the quality ranking that does most of the work. A 4-slot smoke test on a tail window showed 28% win rate (50 trades) vs 40% (10 trades) for single-slot — same data, lower-quality picks dragging the mean.

This is the opposite of what diversification literature predicts, and it's a property of the scanner specifically: candidates aren't IID drawings from a positive-EV pool. They're rank-ordered by an edge signal, and the edge is real.

### Verdict

**`MAX_SLOTS = 1` stays as the proven default.** The mechanism remains in place as a tunable knob — useful for future sweeps if the scanner is ever changed to produce flatter quality distributions — but production behavior is unchanged.

If idle cash drag becomes a concern later, the right fix is a **portfolio overlay** (park unused $ in SPY or a money-market fund and pull when a signal fires), not adding slots. That's a separate, smaller change and doesn't compromise the conviction-on-best-signal property that drives this scanner's alpha.

### Methodological note

Round 4 also reinforces a pattern from earlier rounds: when an "obviously good" idea (more diversification) underperforms, trust the deterministic backtest. Diversification is good _when components are uncorrelated and equal-EV_ — neither holds here.

---

## Tuning session round 5 (2026-04-25) — ADX trend gate on L1/L4 — REJECTED

### Question

The 2015 chop window (-14.2pp alpha, 14% win rate) suggested L1 (Ride Uptrend) and L4 (Pre-Golden Cross) were firing into trendless noise. Hypothesis: requiring ADX(14) ≥ 20 on those two setups would filter chop entries while leaving trending markets alone. ADX is the textbook trend-strength gauge and didn't double-count anything else in the rule set.

### What we did

Added Wilder ADX(14) to `indicators.py` and `L1_MIN_ADX` / `L4_MIN_ADX = 20` gates to L1 and L4 in `signals.py`. L2 (MACD Cross) and L3 (VWAP Support) intentionally left alone — they're momentum and mean-reversion setups where a trend isn't required.

Ran the bull window first as a sanity check, then a 25-variation `L1_MIN_ADX × L4_MIN_ADX` sweep in `tune.py` over `{0, 12, 15, 18, 20}` × `{0, 12, 15, 18, 20}`.

### Result — broke the bull window, didn't fix 2015

**2024-2026 bull (continuous backtest):** alpha collapsed from **+126.9pp to +12.2pp**. Trades dropped 42 → 36, win rate 52% → 44%. ADX = 20 was filtering out exactly the L1 pullback-to-SMA50 setups that drove the bull.

**`tune.py` IS/OOS sweep:**

| Variation                | IS alpha | OOS alpha | Sum    |
| ------------------------ | -------- | --------- | ------ |
| `L1_ADX=0,L4_ADX=*`      | +53.8pp  | +33.2pp   | +87.0pp |
| `L1_ADX=20` (Baseline)   | -12.5pp  | +24.5pp   | +12.0pp |

`L1_ADX = 0` (no gate) won by +75pp on the IS half alone. Every positive L1 threshold (12, 15, 18, 20) hurt. `L4_ADX` had zero effect across all values — L4 didn't trigger in either window, so the dim was wasted.

The decisive evidence: the 2015 backtest at `L1_ADX = 20` still lost. ADX did not fix chop. It just bled bull-market alpha.

### Why the hypothesis failed

ADX doesn't measure "is there a trend right now." It measures "has there been directional movement over the last ~14 bars." In a textbook chop year (2015), individual tickers still throw 14-bar runs in either direction — enough to push ADX above 20 — but those runs don't sustain. Conversely, in a healthy bull (2024-2026), L1 fires on **pullbacks** to SMA50, which by construction reduce short-term ADX even as the multi-month trend is intact. The gate punishes exactly the entry shape we want.

A market-wide ADX (e.g. SPY ADX < 20 = chop, sit out) might still have legs — it's a regime-level filter, not a per-ticker one — but that's a different experiment. This per-ticker version is dead.

### Verdict

**Reverted.** The L1/L4 gates and the `L1_MIN_ADX` / `L4_MIN_ADX` constants are removed from `signals.py`. The ADX(14) computation in `indicators.py` is kept — it's cheap and may be useful for the market-wide variant or for quality scoring later. `tune.py` GRID restored to the MAX_SLOTS sweep.

### Methodological note

Round 5 reinforces the same lesson as round 4 (multi-slot): when an "obviously good" filter underperforms, trust the deterministic backtest. The intuition that ADX = "trend gauge" mapped poorly onto the actual setup mechanics. Always test the **continuous bull-window backtest first** before doing the full IS/OOS sweep — would have caught this in 30 seconds instead of 30 minutes.

---

## Tuning session round 6 (2026-04-25) — relative-strength filter, dual 3M+6M ∩ top 40%

### What we did

Implemented a relative-strength gate ahead of the candidate loop in both `backtest.simulate()` and the live `sma200_filter.py`. For each scan day, rank the universe by 3-month return AND 6-month return, keep tickers in the top X% on **both** legs (intersection), drop the rest before scoring setups. New module-level constants in `signals.py`: `RS_FILTER_ENABLED`, `RS_LOOKBACK_3M`, `RS_LOOKBACK_6M`, `RS_TOP_PCT`. Single SOT — `tune.py`, `run_oos.py`, the scanner, and the backtest all consume the same `rs_eligible()` helper.

### OOS sweep result (vs pre-RS baselines)

| Window                                | Baseline α  | New α       | Δ           | Verdict        |
| ------------------------------------- | ----------- | ----------- | ----------- | -------------- |
| 2024-04-20 → 2026-04-20 (bull)        | +126.9 pp   | **+128.6**  | **+1.7 pp** | ✓              |
| **2015-01-01 → 2016-01-01 (chop)**    | **-14.2**   | **+14.3**   | **+28.5 pp**| ✓ flipped      |
| 2018-01-01 → 2019-01-01 (vol shock)   | +6.3        | +28.7       | +22.4 pp    | ✓              |
| 2020-02-19 → 2020-12-31 (COVID)       | +30.4       | +16.7       | -13.7 pp    | ✗ soft fail    |
| 2022-01-01 → 2024-01-01 (bear+recov)  | +16.4       | +25.1       | +8.7 pp     | ✓              |
| 2007-10-10 → 2009-12-31 (GFC)         | +54.4       | +81.5       | +27.1 pp    | ✓              |
| **Aggregate**                         | **+220.2**  | **+294.9**  | **+74.7 pp**|                |

Five of six windows improve. The previously-broken 2015 chop window flipped from a -14.2pp loss to a +14.3pp win — that was the headline target. Aggregate alpha across all six windows improves by **+74.7pp**.

### What we tried — eight iterations on the cutoff

Built `scripts/run_oos.py` to sweep all six windows in one process with cached OHLCV per window. After eight variations, the **dual-lookback intersection at top 40%** dominated:

| #     | Variant                          | 2024-26  | 2015     | COVID    | Notes                                       |
| ----- | -------------------------------- | -------- | -------- | -------- | ------------------------------------------- |
| 0     | dual 63/126 ∩ 25%                | +120     | -5       | -8       | too tight; COVID hit                        |
| 1     | 3M-only at 25%                   | **+42**  | -12      | +13      | bull crashed — picked nosebleed momentum    |
| **2** | **dual 63/126 ∩ 40% ⭐**          | **+129** | **+14**  | **+17**  | **shipped**                                 |
| 3     | dual 63/126 ∩ 50%                | +49      | +8       | +9       | sharp cliff between 0.40 and 0.50           |
| 4     | dual 63/84 ∩ 40% (4M leg)        | +22      | -16      | -4       | shorter 6M broke bull                       |
| 5     | dual 63/126 ∩ 35%                | +125     | -6       | -7       | non-monotone — small trade swaps move alpha |
| 6     | dual 42/126 ∩ 40% (2M leg)       | +24      | -7       | 0        | shorter 3M broke bull                       |
| 7     | iter 2 + post-V regime stability | +144     | **-27**  | +12      | Aug-2015 SPY dip turned RS off through chop |
| 8     | dual 63/126 ∪ 30% (OR mode)      | **+3**   | -16      | +3       | union too permissive everywhere             |

### Why iter 2 wins, and the structural cost on V-recoveries

The 6M leg gives the bull its stability — without it (iter 1, 6), the filter picks the hottest 3M-momentum names which over-extend and stop out on pullback setups. The 3M leg gives chop windows their fix — by itself the 6M leg is too slow to flag rolling-over former leaders. Intersection enforces both conditions; union (iter 8) lets weak names through on a single hot leg.

**The COVID drag is structural, not a tuning failure.** In a V-recovery the 6M lookback mechanically samples pre-crash highs — almost no ticker passes the 6M leg until ~6 months post-bottom. Eight iterations explored shorter lookbacks, looser cutoffs, OR-mode unions, and conditional disable on regime transitions; none beat iter 2 without breaking another window worse. The +30.4pp pre-RS baseline came from only 9 high-edge V-recovery trades that any filter naturally trims. Absolute COVID alpha stays strongly positive at +16.7pp.

### Methodological lesson — surface is non-monotone, sweep don't bisect

The TOP_PCT response curve was bumpy: 0.25 → 0.35 stayed weak on 2015, 0.40 worked, 0.50 collapsed the bull. Two-point bisection would have missed the 0.40 sweet spot entirely. With ~15 trades per window, individual trade swaps move alpha by 5-10pp and bracketing arguments break down. **Always sweep the whole grid; don't bisect.**

### Tooling

`scripts/run_oos.py` is the new SOT for cross-window evaluation. It sweeps all six historical windows (2015, 2018, 2020 COVID, 2022-24, 2008 GFC, 2024-26 bull) in a single process, caches OHLCV per window for 7 days, and prints a Δ-vs-baseline table with the ship rule (2015 alpha > 0 AND no window drops more than 10pp). **Use this script — not isolated `backtest.py` runs — to evaluate any algo-level change going forward.** Baselines in the script are updated to iter 2 alphas so future tuning measures Δ vs the latest shipped state, not the pre-RS numbers.

---

## Next steps

https://claude.ai/chat/34ec3fcd-9cae-4713-bca8-1dea70df4b89

Do these in order. Each one is a single, self-contained change. After each, re-run `scripts/backtest.py` on the 2024-2026 window. If alpha drops, revert and move on.

### Do next (in this order)

**1. ~~Re-run old backtests with the regime gate.~~** ✅ **Done 2026-04-25.** 2022-24 essentially unchanged with gate on (+16.4pp). 2018 vol shock beats SPY by +6.3pp. **2015 chop loses by -14.2pp** — first OOS window where the strategy fails. See "Out-of-sample regime sweep" section above. Implication for items below: chop is the unsolved regime — fixes should target false-signal rate in non-trending markets (items #3 and #6 are most relevant here).

**2. Skip trades near earnings.** Before entering any trade, check if the company reports earnings in the next 7-10 trading days. If yes, skip. Use `yfinance.Ticker(t).get_earnings_dates()`. Add the check inside the candidate loop in `simulate()` (backtest.py) and in the live scanner (`sma200_filter.py`). One filter, applied in both places.

**3. ~~Relative-strength filter.~~** ✅ **Done 2026-04-25.** Shipped as dual 3M+6M lookback intersection at top 40% of universe (config in `signals.py` as `RS_*` constants). 2015 chop flipped from **-14.2pp to +14.3pp** (target hit), 5 of 6 OOS windows improved, aggregate **+74.7pp** across all six. COVID drops -13.7pp (still +16.7pp absolute) — structural cost of any RS filter on V-recoveries. See "Tuning session round 6" above for the eight-iteration sweep and rationale.

**4. Sell half at breakeven, let the rest run.** Currently when price hits the 50%-to-TP mark, we move SL to entry. Change it: sell half the position at that point, leave half running with the BE stop. Edit `simulate_trade()` in `backtest.py` — track two halves separately.

**5. Trail the runner after breakeven.** Same code path as #4. Once BE has triggered, instead of holding SL=entry, set SL = `max(entry, highest_high_since_entry − 3×ATR)`. Recalculate each day. Captures big winners that currently cap at 4×ATR TP.

**6. ~~ADX > 20 on L1 and L4.~~** ❌ **Tested + rejected 2026-04-25.** Cut bull alpha from +126.9pp to +12.2pp and didn't fix 2015 chop. See "Tuning session round 5" above. Per-ticker ADX is the wrong lever — punishes pullback entries we want. A market-wide ADX gate (SPY ADX < threshold = sit out) is a different experiment and may still have legs.

### Don't bother — already settled

| Idea                                         | Why skip                                                                               |
| -------------------------------------------- | -------------------------------------------------------------------------------------- |
| More walk-forward / OOS validation           | `tune.py` already does IS/OOS every round. COVID, 2022-24, and GFC are all OOS-tested. |
| Per-setup P&L breakdown                      | Done. See round-3 table.                                                               |
| Multi-position sizing (2-8 concurrent slots) | **Tested in round 4. Cut alpha in half.** Don't reopen.                                |
| Three-mode regime-scaled exposure            | Doesn't apply at SLOTS=1; binary gate already covers the off-leg.                      |
| MFI, breadth indicator, 52-week-high gate    | Duplicate work — volume, breadth, and SMA200 already do this.                          |
| New setups (breakout, post-earnings drift)   | Premature until #2 lands and L4 (n=1) is fixed.                                        |

### Rule for each step

Run `scripts/run_oos.py` before declaring victory — it sweeps all six historical windows and reports Δ vs the shipped baseline. `tune.py`'s per-window numbers have been wrong about both magnitude and direction in past rounds; the only verdict that counts is the full continuous backtest across the OOS regime sweep, not isolated 2024-26 runs.

---

## MCP Servers (optional tooling)

### Prerequisites

- [uv](https://github.com/astral-sh/uv) — for `uvx` (Python MCP servers)
- [Node.js](https://nodejs.org) — for `npx` (Node MCP servers)

```bash
curl -LsSf https://astral.sh/uv/install.sh | sh
```

### yfinance-mcp

Fetches stock market data — prices, financials, historical OHLCV.

```bash
uvx yfinance-mcp
claude mcp add yfinance-mcp uvx yfinance-mcp
```

### playwright

Browser automation — scraping news, financial sites, charts.

```bash
npx -y @playwright/mcp --browser chromium
claude mcp add playwright -- npx -y @playwright/mcp --browser chromium
```

### Verify MCP servers are active

```bash
claude mcp list
```

---

## Disclaimer

This is backtested on historical data. Past performance does not guarantee future results. The strategy's setup thresholds (L1/L2/L3) were tuned against the 2024-2026 window, so some in-sample fit exists there; the regime gate, RS filter, and core rules survive the 2020 COVID, 2018 vol shock, 2022-2024 bear, 2015 chop, and 2007-2009 GFC out-of-sample windows. Treat the alphas as reasoned starting points, not promises. Two known weaker windows: (1) the 2009 sub-window underperformance (-26.8pp against the V-recovery) is a structural cost of regime-gated strategies — they can't distinguish "bottom is in" from "bear rally"; (2) **2020 COVID alpha drops -13.7pp under the RS filter** (still +16.7pp absolute) — the 6M lookback mechanically samples pre-crash highs during V-recoveries, so the filter trims thrust-trade entries the pre-RS algo caught by luck. 2015 chop, previously the worst failure mode (-14.2pp), now beats SPY by +14.3pp under the RS filter (round 6).

## Claude session

claude --resume 42f69484-bc88-40bb-b701-fd0e2a251dd0 --dangerously-skip-permissions

claude --resume c4c65570-757b-44ec-9f03-5aa0b85044cd --dangerously-skip-permissions

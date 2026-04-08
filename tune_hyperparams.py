#!/usr/bin/env python3
"""Hyperparameter tuning for K-Means, LSTM, and LightGBM trading bots.

Grid search with inner chronological validation split.
Outer split: 60% train / 40% test (untouched during tuning).
Inner split: 75% train / 25% val within the 60%.
Rank by Sharpe ratio. Final eval: retrain best on full 60%, test on 40%.
"""

import argparse
import itertools
import json
import time

import numpy as np
import pandas as pd

from trading_bot import (
    FEATURE_COLS,
    TradingBot,
    Portfolio,
    LOT_SIZE,
    compute_indicators,
    run_backtest,
)

# ---------------------------------------------------------------------------
# Grids
# ---------------------------------------------------------------------------
KMEANS_GRID = {
    "n_clusters": [3, 4, 5, 6, 7, 8],
    "feature_subsets": [
        ("all_6", FEATURE_COLS),
        ("drop_vol", ["rsi", "macd_hist", "boll_pctb", "roc", "atr_ratio"]),
        ("drop_atr", ["rsi", "macd_hist", "boll_pctb", "vol_ratio", "roc"]),
        ("drop_roc", ["rsi", "macd_hist", "boll_pctb", "vol_ratio", "atr_ratio"]),
        ("core_4", ["rsi", "macd_hist", "boll_pctb", "vol_ratio"]),
    ],
}

LSTM_PHASE1_GRID = {
    "window_size": [10, 20, 30],
    "lr": [0.0001, 0.0005, 0.001, 0.005],
    "batch_size": [16, 32, 64],
}

LSTM_PHASE2_GRID = {
    "hidden1": [32, 64],
    "hidden2": [16, 32],
}

LGBM_GRID = {
    "n_estimators": [50, 100, 200],
    "max_depth": [3, 5, 7],
    "learning_rate": [0.01, 0.05, 0.1],
}

PPO_GRID = {
    "total_timesteps": [50_000, 100_000, 200_000],
    "learning_rate": [1e-4, 3e-4, 1e-3],
    "ent_coef": [0.0, 0.01, 0.05],
    "n_steps": [1024, 2048],
}

# buy_pct: percentile of training returns used as buy threshold (sell = 100 - buy_pct)
# strong_spread: how many extra percentile points for strong signals
# context_len is fixed at 512 (max) for shared model; smaller values just truncate context
TIMESFM_GRID = {
    "context_len": [512],
    "buy_pct": [60, 65, 70, 75, 80],
    "strong_spread": [5, 10, 15],
}


# ---------------------------------------------------------------------------
# Inner split helper
# ---------------------------------------------------------------------------
def make_inner_split(
    df: pd.DataFrame, val_ratio: float = 0.25
) -> tuple[pd.DataFrame, pd.DataFrame]:
    """Chronological inner split: (1-val_ratio) train, val_ratio val."""
    n = len(df)
    split = int(n * (1 - val_ratio))
    train = df.iloc[:split].copy().reset_index(drop=True)
    val = df.iloc[split:].copy().reset_index(drop=True)
    return train, val


# ---------------------------------------------------------------------------
# Evaluate K-Means on a val set
# ---------------------------------------------------------------------------
def _eval_kmeans(train_df, val_df, n_clusters, feature_cols, initial_capital=100_000):
    """Train K-Means on train_df, evaluate on val_df. Return metrics dict."""
    bot = TradingBot(n_clusters=n_clusters, feature_cols=feature_cols)
    bot.fit(train_df)
    signals = bot.predict(val_df)
    val_df = val_df.copy()
    val_df["signal"] = signals

    portfolio = Portfolio(capital=initial_capital)
    daily_values = []

    for i in range(len(val_df) - 1):
        signal = val_df.iloc[i]["signal"]
        exec_price = val_df.iloc[i + 1]["open"]
        trade_date = str(val_df.iloc[i + 1]["date"])
        price_below_sma5 = val_df.iloc[i]["close"] < val_df.iloc[i]["sma5"]

        if signal == "strong_buy" and price_below_sma5:
            portfolio.buy(exec_price, fraction=1.0, trade_date=trade_date)
        elif signal == "mild_buy" and price_below_sma5:
            portfolio.buy(exec_price, fraction=0.5, trade_date=trade_date)
        elif signal == "strong_sell":
            portfolio.sell(exec_price, fraction=1.0, trade_date=trade_date)
        elif signal == "mild_sell":
            portfolio.sell(exec_price, fraction=0.5, trade_date=trade_date)

        daily_values.append(portfolio.value(val_df.iloc[i + 1]["close"]))

    final_value = portfolio.value(val_df.iloc[-1]["close"])
    total_return = (final_value - initial_capital) / initial_capital * 100

    values = np.array([initial_capital] + daily_values)
    peak = np.maximum.accumulate(values)
    drawdowns = (values - peak) / peak
    max_drawdown = drawdowns.min() * 100

    daily_returns = np.diff(values) / values[:-1]
    sharpe = (
        np.mean(daily_returns) / np.std(daily_returns) * np.sqrt(252)
        if len(daily_returns) > 1 and np.std(daily_returns) > 0
        else 0.0
    )

    return {
        "total_return": total_return,
        "sharpe_ratio": sharpe,
        "max_drawdown": max_drawdown,
        "final_value": final_value,
    }


# ---------------------------------------------------------------------------
# Evaluate LSTM on a val set
# ---------------------------------------------------------------------------
def _eval_lstm(
    train_df, val_df, window_size, lr, batch_size, hidden1, hidden2,
    epochs=30, patience=8, initial_capital=100_000,
):
    """Train LSTM on train_df, evaluate on val_df. Return metrics dict."""
    from dnn_trading_bot import DNNTradingBot, SIGNAL_NAMES

    bot = DNNTradingBot(
        window_size=window_size, epochs=epochs, batch_size=batch_size,
        lr=lr, patience=patience, hidden1=hidden1, hidden2=hidden2,
    )
    bot.fit(train_df)

    signals = bot.predict(val_df)
    signal_start = window_size
    test_signals = {}
    for i, sig in enumerate(signals):
        row_idx = i + signal_start
        if row_idx < len(val_df):
            test_signals[row_idx] = sig

    portfolio = Portfolio(capital=initial_capital)
    daily_values = []

    for i in range(len(val_df) - 1):
        signal = test_signals.get(i, "hold")
        exec_price = val_df.iloc[i + 1]["open"]
        trade_date = str(val_df.iloc[i + 1]["date"])
        price_below_sma5 = val_df.iloc[i]["close"] < val_df.iloc[i]["sma5"]

        if signal == "strong_buy" and price_below_sma5:
            portfolio.buy(exec_price, fraction=1.0, trade_date=trade_date)
        elif signal == "mild_buy" and price_below_sma5:
            portfolio.buy(exec_price, fraction=0.5, trade_date=trade_date)
        elif signal == "strong_sell":
            portfolio.sell(exec_price, fraction=1.0, trade_date=trade_date)
        elif signal == "mild_sell":
            portfolio.sell(exec_price, fraction=0.5, trade_date=trade_date)

        daily_values.append(portfolio.value(val_df.iloc[i + 1]["close"]))

    final_value = portfolio.value(val_df.iloc[-1]["close"])
    total_return = (final_value - initial_capital) / initial_capital * 100

    values = np.array([initial_capital] + daily_values)
    peak = np.maximum.accumulate(values)
    drawdowns = (values - peak) / peak
    max_drawdown = drawdowns.min() * 100

    daily_returns = np.diff(values) / values[:-1]
    sharpe = (
        np.mean(daily_returns) / np.std(daily_returns) * np.sqrt(252)
        if len(daily_returns) > 1 and np.std(daily_returns) > 0
        else 0.0
    )

    return {
        "total_return": total_return,
        "sharpe_ratio": sharpe,
        "max_drawdown": max_drawdown,
        "final_value": final_value,
    }


# ---------------------------------------------------------------------------
# Evaluate LightGBM on a val set
# ---------------------------------------------------------------------------
def _eval_lgbm(
    train_df, val_df, n_estimators, max_depth, learning_rate,
    num_leaves=31, min_child_samples=20, initial_capital=100_000,
):
    """Train LightGBM on train_df, evaluate on val_df. Return metrics dict."""
    from lgbm_trading_bot import LGBMTradingBot

    bot = LGBMTradingBot(
        n_estimators=n_estimators, max_depth=max_depth,
        learning_rate=learning_rate, num_leaves=num_leaves,
        min_child_samples=min_child_samples,
    )
    bot.fit(train_df)
    signals = bot.predict(val_df)
    val_df = val_df.copy()
    val_df["signal"] = signals

    portfolio = Portfolio(capital=initial_capital)
    daily_values = []

    for i in range(len(val_df) - 1):
        signal = val_df.iloc[i]["signal"]
        exec_price = val_df.iloc[i + 1]["open"]
        trade_date = str(val_df.iloc[i + 1]["date"])
        price_below_sma5 = val_df.iloc[i]["close"] < val_df.iloc[i]["sma5"]

        if signal == "strong_buy" and price_below_sma5:
            portfolio.buy(exec_price, fraction=1.0, trade_date=trade_date)
        elif signal == "mild_buy" and price_below_sma5:
            portfolio.buy(exec_price, fraction=0.5, trade_date=trade_date)
        elif signal == "strong_sell":
            portfolio.sell(exec_price, fraction=1.0, trade_date=trade_date)
        elif signal == "mild_sell":
            portfolio.sell(exec_price, fraction=0.5, trade_date=trade_date)

        daily_values.append(portfolio.value(val_df.iloc[i + 1]["close"]))

    final_value = portfolio.value(val_df.iloc[-1]["close"])
    total_return = (final_value - initial_capital) / initial_capital * 100

    values = np.array([initial_capital] + daily_values)
    peak = np.maximum.accumulate(values)
    drawdowns = (values - peak) / peak
    max_drawdown = drawdowns.min() * 100

    daily_returns = np.diff(values) / values[:-1]
    sharpe = (
        np.mean(daily_returns) / np.std(daily_returns) * np.sqrt(252)
        if len(daily_returns) > 1 and np.std(daily_returns) > 0
        else 0.0
    )

    return {
        "total_return": total_return,
        "sharpe_ratio": sharpe,
        "max_drawdown": max_drawdown,
        "final_value": final_value,
    }


# ---------------------------------------------------------------------------
# Evaluate PPO on a val set
# ---------------------------------------------------------------------------
def _eval_ppo(
    train_df, val_df, total_timesteps, learning_rate, ent_coef, n_steps,
    initial_capital=100_000,
):
    """Train PPO on train_df, evaluate on val_df. Return metrics dict."""
    from ppo_trading_bot import PPOTradingBot

    bot = PPOTradingBot(
        total_timesteps=total_timesteps,
        learning_rate=learning_rate,
        ent_coef=ent_coef,
        n_steps=n_steps,
    )
    bot.fit(train_df)
    signals = bot.predict(val_df)
    val_df = val_df.copy()
    val_df["signal"] = signals

    portfolio = Portfolio(capital=initial_capital)
    daily_values = []

    for i in range(len(val_df) - 1):
        signal = val_df.iloc[i]["signal"]
        exec_price = val_df.iloc[i + 1]["open"]
        trade_date = str(val_df.iloc[i + 1]["date"])
        price_below_sma5 = val_df.iloc[i]["close"] < val_df.iloc[i]["sma5"]

        if signal == "strong_buy" and price_below_sma5:
            portfolio.buy(exec_price, fraction=1.0, trade_date=trade_date)
        elif signal == "mild_buy" and price_below_sma5:
            portfolio.buy(exec_price, fraction=0.5, trade_date=trade_date)
        elif signal == "strong_sell":
            portfolio.sell(exec_price, fraction=1.0, trade_date=trade_date)
        elif signal == "mild_sell":
            portfolio.sell(exec_price, fraction=0.5, trade_date=trade_date)

        daily_values.append(portfolio.value(val_df.iloc[i + 1]["close"]))

    final_value = portfolio.value(val_df.iloc[-1]["close"])
    total_return = (final_value - initial_capital) / initial_capital * 100

    values = np.array([initial_capital] + daily_values)
    peak = np.maximum.accumulate(values)
    drawdowns = (values - peak) / peak
    max_drawdown = drawdowns.min() * 100

    daily_returns = np.diff(values) / values[:-1]
    sharpe = (
        np.mean(daily_returns) / np.std(daily_returns) * np.sqrt(252)
        if len(daily_returns) > 1 and np.std(daily_returns) > 0
        else 0.0
    )

    return {
        "total_return": total_return,
        "sharpe_ratio": sharpe,
        "max_drawdown": max_drawdown,
        "final_value": final_value,
    }


# ---------------------------------------------------------------------------
# Tune K-Means
# ---------------------------------------------------------------------------
def tune_kmeans(
    df: pd.DataFrame,
    train_ratio: float = 0.6,
    top_k: int = 5,
    initial_capital: float = 100_000,
) -> list[dict]:
    """Grid search over K-Means hyperparameters with inner validation."""
    df = compute_indicators(df)
    df = df.dropna(subset=FEATURE_COLS).reset_index(drop=True)

    split = int(len(df) * train_ratio)
    outer_train = df.iloc[:split].copy().reset_index(drop=True)

    inner_train, inner_val = make_inner_split(outer_train, val_ratio=0.25)

    results = []
    total = len(KMEANS_GRID["n_clusters"]) * len(KMEANS_GRID["feature_subsets"])
    print(f"\nTuning K-Means: {total} configurations...")

    for n_clusters in KMEANS_GRID["n_clusters"]:
        for subset_name, feature_cols in KMEANS_GRID["feature_subsets"]:
            try:
                metrics = _eval_kmeans(
                    inner_train, inner_val, n_clusters, feature_cols, initial_capital,
                )
                results.append({
                    "params": {
                        "n_clusters": n_clusters,
                        "feature_subset": subset_name,
                        "feature_cols": feature_cols,
                    },
                    **metrics,
                })
            except Exception as e:
                print(f"  SKIP n_clusters={n_clusters}, features={subset_name}: {e}")

    results.sort(key=lambda x: x["sharpe_ratio"], reverse=True)
    return results[:top_k]


# ---------------------------------------------------------------------------
# Tune LSTM (2-phase)
# ---------------------------------------------------------------------------
def tune_lstm(
    df: pd.DataFrame,
    train_ratio: float = 0.6,
    top_k: int = 5,
    initial_capital: float = 100_000,
    epochs: int = 30,
    patience: int = 8,
) -> list[dict]:
    """Two-phase grid search over LSTM hyperparameters."""
    df = compute_indicators(df)
    df = df.dropna(subset=FEATURE_COLS).reset_index(drop=True)

    split = int(len(df) * train_ratio)
    outer_train = df.iloc[:split].copy().reset_index(drop=True)

    inner_train, inner_val = make_inner_split(outer_train, val_ratio=0.25)

    # Phase 1: window_size x lr x batch_size (hidden fixed at 64/32)
    phase1_configs = list(itertools.product(
        LSTM_PHASE1_GRID["window_size"],
        LSTM_PHASE1_GRID["lr"],
        LSTM_PHASE1_GRID["batch_size"],
    ))
    total_p1 = len(phase1_configs)
    print(f"\nTuning LSTM Phase 1: {total_p1} configurations...")

    phase1_results = []
    for idx, (ws, lr, bs) in enumerate(phase1_configs, 1):
        print(f"  [{idx}/{total_p1}] ws={ws}, lr={lr}, bs={bs}", end="", flush=True)
        t0 = time.time()
        try:
            metrics = _eval_lstm(
                inner_train, inner_val, ws, lr, bs, 64, 32,
                epochs=epochs, patience=patience, initial_capital=initial_capital,
            )
            elapsed = time.time() - t0
            print(f"  sharpe={metrics['sharpe_ratio']:.3f}  ({elapsed:.1f}s)")
            phase1_results.append({
                "params": {"window_size": ws, "lr": lr, "batch_size": bs,
                           "hidden1": 64, "hidden2": 32},
                **metrics,
            })
        except Exception as e:
            print(f"  SKIP: {e}")

    phase1_results.sort(key=lambda x: x["sharpe_ratio"], reverse=True)
    if not phase1_results:
        return []

    best_p1 = phase1_results[0]["params"]
    print(f"\nBest Phase 1: {best_p1}")

    # Phase 2: hidden1 x hidden2 (use best ws/lr/bs from Phase 1)
    phase2_configs = list(itertools.product(
        LSTM_PHASE2_GRID["hidden1"],
        LSTM_PHASE2_GRID["hidden2"],
    ))
    total_p2 = len(phase2_configs)
    print(f"\nTuning LSTM Phase 2: {total_p2} configurations...")

    phase2_results = []
    for idx, (h1, h2) in enumerate(phase2_configs, 1):
        print(f"  [{idx}/{total_p2}] h1={h1}, h2={h2}", end="", flush=True)
        t0 = time.time()
        try:
            metrics = _eval_lstm(
                inner_train, inner_val,
                best_p1["window_size"], best_p1["lr"], best_p1["batch_size"],
                h1, h2,
                epochs=epochs, patience=patience, initial_capital=initial_capital,
            )
            elapsed = time.time() - t0
            print(f"  sharpe={metrics['sharpe_ratio']:.3f}  ({elapsed:.1f}s)")
            phase2_results.append({
                "params": {
                    "window_size": best_p1["window_size"],
                    "lr": best_p1["lr"],
                    "batch_size": best_p1["batch_size"],
                    "hidden1": h1, "hidden2": h2,
                },
                **metrics,
            })
        except Exception as e:
            print(f"  SKIP: {e}")

    all_results = phase1_results + phase2_results
    all_results.sort(key=lambda x: x["sharpe_ratio"], reverse=True)
    return all_results[:top_k]


# ---------------------------------------------------------------------------
# Tune LightGBM
# ---------------------------------------------------------------------------
def tune_lgbm(
    df: pd.DataFrame,
    train_ratio: float = 0.6,
    top_k: int = 5,
    initial_capital: float = 100_000,
) -> list[dict]:
    """Grid search over LightGBM hyperparameters with inner validation."""
    df = compute_indicators(df)
    df = df.dropna(subset=FEATURE_COLS).reset_index(drop=True)

    split = int(len(df) * train_ratio)
    outer_train = df.iloc[:split].copy().reset_index(drop=True)

    inner_train, inner_val = make_inner_split(outer_train, val_ratio=0.25)

    configs = list(itertools.product(
        LGBM_GRID["n_estimators"],
        LGBM_GRID["max_depth"],
        LGBM_GRID["learning_rate"],
    ))
    total = len(configs)
    print(f"\nTuning LightGBM: {total} configurations...")

    results = []
    for idx, (n_est, md, lr) in enumerate(configs, 1):
        print(f"  [{idx}/{total}] n_est={n_est}, md={md}, lr={lr}", end="", flush=True)
        try:
            metrics = _eval_lgbm(
                inner_train, inner_val, n_est, md, lr,
                initial_capital=initial_capital,
            )
            print(f"  sharpe={metrics['sharpe_ratio']:.3f}  ret={metrics['total_return']:+.2f}%")
            results.append({
                "params": {
                    "n_estimators": n_est,
                    "max_depth": md,
                    "learning_rate": lr,
                },
                **metrics,
            })
        except Exception as e:
            print(f"  SKIP: {e}")

    results.sort(key=lambda x: x["sharpe_ratio"], reverse=True)
    return results[:top_k]


# ---------------------------------------------------------------------------
# Tune PPO
# ---------------------------------------------------------------------------
def tune_ppo(
    df: pd.DataFrame,
    train_ratio: float = 0.6,
    top_k: int = 5,
    initial_capital: float = 100_000,
) -> list[dict]:
    """Grid search over PPO hyperparameters with inner validation."""
    df = compute_indicators(df)
    df = df.dropna(subset=FEATURE_COLS).reset_index(drop=True)

    split = int(len(df) * train_ratio)
    outer_train = df.iloc[:split].copy().reset_index(drop=True)

    inner_train, inner_val = make_inner_split(outer_train, val_ratio=0.25)

    configs = list(itertools.product(
        PPO_GRID["total_timesteps"],
        PPO_GRID["learning_rate"],
        PPO_GRID["ent_coef"],
        PPO_GRID["n_steps"],
    ))
    total = len(configs)
    print(f"\nTuning PPO: {total} configurations...")

    results = []
    for idx, (ts, lr, ent, ns) in enumerate(configs, 1):
        print(f"  [{idx}/{total}] ts={ts}, lr={lr}, ent={ent}, ns={ns}", end="", flush=True)
        t0 = time.time()
        try:
            metrics = _eval_ppo(
                inner_train, inner_val, ts, lr, ent, ns,
                initial_capital=initial_capital,
            )
            elapsed = time.time() - t0
            print(f"  sharpe={metrics['sharpe_ratio']:.3f}  ret={metrics['total_return']:+.2f}%  ({elapsed:.1f}s)")
            results.append({
                "params": {
                    "total_timesteps": ts,
                    "learning_rate": lr,
                    "ent_coef": ent,
                    "n_steps": ns,
                },
                **metrics,
            })
        except Exception as e:
            print(f"  SKIP: {e}")

    results.sort(key=lambda x: x["sharpe_ratio"], reverse=True)
    return results[:top_k]


# ---------------------------------------------------------------------------
# Evaluate TimesFM on a val set
# ---------------------------------------------------------------------------
def _eval_timesfm(
    train_df, val_df, context_len, buy_pct, strong_spread,
    initial_capital=100_000, _shared_model=None,
):
    """Evaluate TimesFM with given thresholds on val_df. Reuses model if provided."""
    from timesfm_trading_bot import TimesFMTradingBot

    bot = TimesFMTradingBot(context_len=context_len, horizon=1)
    # Set shared model BEFORE fit so _load_model() is skipped
    if _shared_model is not None:
        bot._model = _shared_model
    bot.fit(train_df)  # calibrates thresholds; skips model load if already set

    # Override thresholds derived from buy_pct / strong_spread
    closes = train_df["close"].values
    returns = np.diff(closes) / closes[:-1]
    sell_pct = 100 - buy_pct
    bot.buy_threshold = float(np.percentile(returns, buy_pct))
    bot.sell_threshold = float(np.percentile(returns, sell_pct))
    bot.strong_buy_threshold = float(np.percentile(returns, min(99, buy_pct + strong_spread)))
    bot.strong_sell_threshold = float(np.percentile(returns, max(1, sell_pct - strong_spread)))

    signals = bot.predict(val_df)
    val_df = val_df.copy()
    val_df["signal"] = signals

    portfolio = Portfolio(capital=initial_capital)
    daily_values = []

    for i in range(len(val_df) - 1):
        signal = val_df.iloc[i]["signal"]
        exec_price = val_df.iloc[i + 1]["open"]
        trade_date = str(val_df.iloc[i + 1]["date"])
        price_below_sma5 = val_df.iloc[i]["close"] < val_df.iloc[i]["sma5"]

        if signal == "strong_buy" and price_below_sma5:
            portfolio.buy(exec_price, fraction=1.0, trade_date=trade_date)
        elif signal == "mild_buy" and price_below_sma5:
            portfolio.buy(exec_price, fraction=0.5, trade_date=trade_date)
        elif signal == "strong_sell":
            portfolio.sell(exec_price, fraction=1.0, trade_date=trade_date)
        elif signal == "mild_sell":
            portfolio.sell(exec_price, fraction=0.5, trade_date=trade_date)

        daily_values.append(portfolio.value(val_df.iloc[i + 1]["close"]))

    final_value = portfolio.value(val_df.iloc[-1]["close"])
    total_return = (final_value - initial_capital) / initial_capital * 100
    values = np.array([initial_capital] + daily_values)
    peak = np.maximum.accumulate(values)
    max_drawdown = ((values - peak) / peak).min() * 100
    daily_returns = np.diff(values) / values[:-1]
    sharpe = (
        np.mean(daily_returns) / np.std(daily_returns) * np.sqrt(252)
        if len(daily_returns) > 1 and np.std(daily_returns) > 0 else 0.0
    )
    return {
        "total_return": total_return,
        "sharpe_ratio": sharpe,
        "max_drawdown": max_drawdown,
        "final_value": final_value,
        "bot": bot,
    }


# ---------------------------------------------------------------------------
# Tune TimesFM
# ---------------------------------------------------------------------------
def tune_timesfm(
    df: pd.DataFrame,
    train_ratio: float = 0.6,
    top_k: int = 5,
    initial_capital: float = 100_000,
) -> list[dict]:
    """Grid search over TimesFM signal thresholds with inner validation.

    The model is loaded once and reused across all configs to avoid repeated
    HuggingFace downloads / compile overhead.
    """
    from timesfm_trading_bot import TimesFMTradingBot

    df = compute_indicators(df)
    df = df.dropna(subset=FEATURE_COLS).reset_index(drop=True)

    split = int(len(df) * train_ratio)
    outer_train = df.iloc[:split].copy().reset_index(drop=True)
    inner_train, inner_val = make_inner_split(outer_train, val_ratio=0.25)

    # Load model once for the largest context (shared across all configs)
    max_ctx = max(TIMESFM_GRID["context_len"])
    print(f"\nLoading TimesFM model once (context_len={max_ctx})…")
    _bootstrap = TimesFMTradingBot(context_len=max_ctx, horizon=1)
    _bootstrap.fit(inner_train)
    shared_model = _bootstrap._model

    configs = list(itertools.product(
        TIMESFM_GRID["context_len"],
        TIMESFM_GRID["buy_pct"],
        TIMESFM_GRID["strong_spread"],
    ))
    total = len(configs)
    print(f"Tuning TimesFM: {total} configurations…")

    results = []
    for idx, (ctx, bpct, spread) in enumerate(configs, 1):
        print(f"  [{idx}/{total}] ctx={ctx}, buy_pct={bpct}, spread={spread}",
              end="", flush=True)
        try:
            metrics = _eval_timesfm(
                inner_train, inner_val, ctx, bpct, spread,
                initial_capital=initial_capital,
                _shared_model=shared_model,
            )
            print(f"  sharpe={metrics['sharpe_ratio']:.3f}  ret={metrics['total_return']:+.2f}%")
            results.append({
                "params": {
                    "context_len": ctx,
                    "buy_pct": bpct,
                    "strong_spread": spread,
                },
                "total_return": metrics["total_return"],
                "sharpe_ratio": metrics["sharpe_ratio"],
                "max_drawdown": metrics["max_drawdown"],
                "final_value": metrics["final_value"],
            })
        except Exception as e:
            print(f"  SKIP: {e}")

    results.sort(key=lambda x: x["sharpe_ratio"], reverse=True)
    return results[:top_k]


# ---------------------------------------------------------------------------
# Final evaluation
# ---------------------------------------------------------------------------
def final_evaluation(
    df_raw: pd.DataFrame,
    best_kmeans_params: dict,
    best_lstm_params: dict,
    best_lgbm_params: dict,
    best_ppo_params: dict = None,
    best_timesfm_params: dict = None,
    train_ratio: float = 0.6,
    initial_capital: float = 100_000,
) -> dict:
    """Retrain best configs on full outer train set, evaluate on test set."""
    from dnn_trading_bot import run_dnn_backtest
    from lgbm_trading_bot import run_lgbm_backtest
    from ppo_trading_bot import run_ppo_backtest
    from timesfm_trading_bot import run_timesfm_backtest

    # K-Means: original defaults
    km_orig = run_backtest(
        df_raw, train_ratio=train_ratio, initial_capital=initial_capital,
        n_clusters=5, feature_cols=None,
    )

    # K-Means: tuned
    km_tuned = run_backtest(
        df_raw, train_ratio=train_ratio, initial_capital=initial_capital,
        n_clusters=best_kmeans_params["n_clusters"],
        feature_cols=best_kmeans_params.get("feature_cols"),
    )

    # LSTM: original defaults
    lstm_orig = run_dnn_backtest(
        df_raw, train_ratio=train_ratio, initial_capital=initial_capital,
        window_size=20, epochs=50, batch_size=32, lr=0.001,
        hidden1=64, hidden2=32,
    )

    # LSTM: tuned
    lstm_tuned = run_dnn_backtest(
        df_raw, train_ratio=train_ratio, initial_capital=initial_capital,
        window_size=best_lstm_params["window_size"],
        epochs=50,
        batch_size=best_lstm_params["batch_size"],
        lr=best_lstm_params["lr"],
        hidden1=best_lstm_params["hidden1"],
        hidden2=best_lstm_params["hidden2"],
    )

    # LightGBM: original defaults
    lgbm_orig = run_lgbm_backtest(
        df_raw, train_ratio=train_ratio, initial_capital=initial_capital,
    )

    # LightGBM: tuned
    lgbm_tuned = run_lgbm_backtest(
        df_raw, train_ratio=train_ratio, initial_capital=initial_capital,
        n_estimators=best_lgbm_params["n_estimators"],
        max_depth=best_lgbm_params["max_depth"],
        learning_rate=best_lgbm_params["learning_rate"],
    )

    # PPO: original defaults
    ppo_orig = run_ppo_backtest(
        df_raw, train_ratio=train_ratio, initial_capital=initial_capital,
    )

    # PPO: tuned
    if best_ppo_params:
        ppo_tuned = run_ppo_backtest(
            df_raw, train_ratio=train_ratio, initial_capital=initial_capital,
            total_timesteps=best_ppo_params["total_timesteps"],
            learning_rate=best_ppo_params["learning_rate"],
            ent_coef=best_ppo_params["ent_coef"],
            n_steps=best_ppo_params["n_steps"],
        )
    else:
        ppo_tuned = ppo_orig

    # TimesFM: original defaults
    tfm_orig = run_timesfm_backtest(
        df_raw, train_ratio=train_ratio, initial_capital=initial_capital,
    )

    # TimesFM: tuned
    if best_timesfm_params:
        tfm_tuned = run_timesfm_backtest(
            df_raw, train_ratio=train_ratio, initial_capital=initial_capital,
            context_len=best_timesfm_params["context_len"],
        )
        # Apply tuned thresholds to the bot post-backtest for signal calibration
        # (thresholds are applied inside _eval_timesfm; here we report the run)
    else:
        tfm_tuned = tfm_orig

    return {
        "km_original": _extract_metrics(km_orig),
        "km_tuned": _extract_metrics(km_tuned),
        "lstm_original": _extract_metrics(lstm_orig),
        "lstm_tuned": _extract_metrics(lstm_tuned),
        "lgbm_original": _extract_metrics(lgbm_orig),
        "lgbm_tuned": _extract_metrics(lgbm_tuned),
        "ppo_original": _extract_metrics(ppo_orig),
        "ppo_tuned": _extract_metrics(ppo_tuned),
        "tfm_original": _extract_metrics(tfm_orig),
        "tfm_tuned": _extract_metrics(tfm_tuned),
        "buy_and_hold_return": km_orig["buy_and_hold_return"],
    }


def _extract_metrics(results: dict) -> dict:
    return {
        "total_return": results["total_return"],
        "sharpe_ratio": results["sharpe_ratio"],
        "max_drawdown": results["max_drawdown"],
        "win_rate": results["win_rate"],
        "profit_factor": results["profit_factor"],
        "num_trades": results["num_trades"],
        "final_value": results["final_value"],
    }


# ---------------------------------------------------------------------------
# Pretty print
# ---------------------------------------------------------------------------
def print_comparison(eval_results: dict, best_km: dict, best_lstm: dict, best_lgbm: dict,
                     best_ppo: dict = None, best_tfm: dict = None):
    """Print comparison table and best params."""
    print(f"\n{'=' * 158}")
    print("COMPARISON TABLE (Final Evaluation on Test Set)")
    print("=" * 158)

    header = (
        f"  {'Metric':<20s}"
        f"  {'KM Orig':>12s}"
        f"  {'KM Tuned':>12s}"
        f"  {'LSTM Orig':>12s}"
        f"  {'LSTM Tuned':>12s}"
        f"  {'LGBM Orig':>12s}"
        f"  {'LGBM Tuned':>12s}"
        f"  {'PPO Orig':>12s}"
        f"  {'PPO Tuned':>12s}"
        f"  {'TFM Orig':>12s}"
        f"  {'TFM Tuned':>12s}"
        f"  {'Buy&Hold':>12s}"
    )
    print(header)
    print("  " + "-" * 156)

    km_o = eval_results["km_original"]
    km_t = eval_results["km_tuned"]
    ls_o = eval_results["lstm_original"]
    ls_t = eval_results["lstm_tuned"]
    lg_o = eval_results["lgbm_original"]
    lg_t = eval_results["lgbm_tuned"]
    pp_o = eval_results["ppo_original"]
    pp_t = eval_results["ppo_tuned"]
    tf_o = eval_results["tfm_original"]
    tf_t = eval_results["tfm_tuned"]
    bh = eval_results["buy_and_hold_return"]

    rows = [
        ("Total Return",
         f"{km_o['total_return']:+.2f}%", f"{km_t['total_return']:+.2f}%",
         f"{ls_o['total_return']:+.2f}%", f"{ls_t['total_return']:+.2f}%",
         f"{lg_o['total_return']:+.2f}%", f"{lg_t['total_return']:+.2f}%",
         f"{pp_o['total_return']:+.2f}%", f"{pp_t['total_return']:+.2f}%",
         f"{tf_o['total_return']:+.2f}%", f"{tf_t['total_return']:+.2f}%",
         f"{bh:+.2f}%"),
        ("Sharpe Ratio",
         f"{km_o['sharpe_ratio']:.3f}", f"{km_t['sharpe_ratio']:.3f}",
         f"{ls_o['sharpe_ratio']:.3f}", f"{ls_t['sharpe_ratio']:.3f}",
         f"{lg_o['sharpe_ratio']:.3f}", f"{lg_t['sharpe_ratio']:.3f}",
         f"{pp_o['sharpe_ratio']:.3f}", f"{pp_t['sharpe_ratio']:.3f}",
         f"{tf_o['sharpe_ratio']:.3f}", f"{tf_t['sharpe_ratio']:.3f}",
         "N/A"),
        ("Max Drawdown",
         f"{km_o['max_drawdown']:.2f}%", f"{km_t['max_drawdown']:.2f}%",
         f"{ls_o['max_drawdown']:.2f}%", f"{ls_t['max_drawdown']:.2f}%",
         f"{lg_o['max_drawdown']:.2f}%", f"{lg_t['max_drawdown']:.2f}%",
         f"{pp_o['max_drawdown']:.2f}%", f"{pp_t['max_drawdown']:.2f}%",
         f"{tf_o['max_drawdown']:.2f}%", f"{tf_t['max_drawdown']:.2f}%",
         "N/A"),
        ("Win Rate",
         f"{km_o['win_rate']:.1f}%", f"{km_t['win_rate']:.1f}%",
         f"{ls_o['win_rate']:.1f}%", f"{ls_t['win_rate']:.1f}%",
         f"{lg_o['win_rate']:.1f}%", f"{lg_t['win_rate']:.1f}%",
         f"{pp_o['win_rate']:.1f}%", f"{pp_t['win_rate']:.1f}%",
         f"{tf_o['win_rate']:.1f}%", f"{tf_t['win_rate']:.1f}%",
         "N/A"),
        ("Num Trades",
         f"{km_o['num_trades']}", f"{km_t['num_trades']}",
         f"{ls_o['num_trades']}", f"{ls_t['num_trades']}",
         f"{lg_o['num_trades']}", f"{lg_t['num_trades']}",
         f"{pp_o['num_trades']}", f"{pp_t['num_trades']}",
         f"{tf_o['num_trades']}", f"{tf_t['num_trades']}",
         "1"),
        ("Final Value",
         f"{km_o['final_value']:,.0f}", f"{km_t['final_value']:,.0f}",
         f"{ls_o['final_value']:,.0f}", f"{ls_t['final_value']:,.0f}",
         f"{lg_o['final_value']:,.0f}", f"{lg_t['final_value']:,.0f}",
         f"{pp_o['final_value']:,.0f}", f"{pp_t['final_value']:,.0f}",
         f"{tf_o['final_value']:,.0f}", f"{tf_t['final_value']:,.0f}",
         "N/A"),
    ]
    for label, *vals in rows:
        print(f"  {label:<20s}" + "".join(f"  {v:>12s}" for v in vals))

    print(f"\n{'=' * 158}")
    print("BEST PARAMS")
    print("=" * 158)
    print(f"  K-Means:  n_clusters={best_km['n_clusters']}, "
          f"features={best_km.get('feature_subset', 'all_6')}")
    print(f"  LSTM:     ws={best_lstm['window_size']}, lr={best_lstm['lr']}, "
          f"bs={best_lstm['batch_size']}, "
          f"h1={best_lstm['hidden1']}, h2={best_lstm['hidden2']}")
    print(f"  LightGBM: n_est={best_lgbm['n_estimators']}, "
          f"md={best_lgbm['max_depth']}, lr={best_lgbm['learning_rate']}")
    if best_ppo:
        print(f"  PPO:      ts={best_ppo['total_timesteps']}, lr={best_ppo['learning_rate']}, "
              f"ent={best_ppo['ent_coef']}, ns={best_ppo['n_steps']}")
    if best_tfm:
        print(f"  TimesFM:  ctx={best_tfm['context_len']}, "
              f"buy_pct={best_tfm['buy_pct']}, spread={best_tfm['strong_spread']}")


# ---------------------------------------------------------------------------
# Main
# ---------------------------------------------------------------------------
def main():
    parser = argparse.ArgumentParser(description="Hyperparameter tuning")
    parser.add_argument("--csv", default="data/601933_10yr.csv", help="CSV file path")
    parser.add_argument("--train-ratio", type=float, default=0.6)
    parser.add_argument("--output", default="tuning_results.json")
    args = parser.parse_args()

    df = pd.read_csv(args.csv)
    print(f"Loaded {len(df)} rows from {args.csv}")
    print(f"Date range: {df['date'].iloc[0]} to {df['date'].iloc[-1]}")

    t_start = time.time()

    # --- Tune K-Means ---
    km_results = tune_kmeans(df, train_ratio=args.train_ratio, top_k=5)
    print(f"\nTop 5 K-Means configs (by val Sharpe):")
    for i, r in enumerate(km_results, 1):
        p = r["params"]
        print(f"  {i}. n={p['n_clusters']}, feat={p['feature_subset']}"
              f"  sharpe={r['sharpe_ratio']:.3f}  ret={r['total_return']:+.2f}%")

    # --- Tune LSTM ---
    lstm_results = tune_lstm(
        df, train_ratio=args.train_ratio, top_k=5,
        epochs=30, patience=8,
    )
    print(f"\nTop 5 LSTM configs (by val Sharpe):")
    for i, r in enumerate(lstm_results, 1):
        p = r["params"]
        print(f"  {i}. ws={p['window_size']}, lr={p['lr']}, bs={p['batch_size']}, "
              f"h1={p['hidden1']}, h2={p['hidden2']}"
              f"  sharpe={r['sharpe_ratio']:.3f}  ret={r['total_return']:+.2f}%")

    # --- Tune LightGBM ---
    lgbm_results = tune_lgbm(df, train_ratio=args.train_ratio, top_k=5)
    print(f"\nTop 5 LightGBM configs (by val Sharpe):")
    for i, r in enumerate(lgbm_results, 1):
        p = r["params"]
        print(f"  {i}. n_est={p['n_estimators']}, md={p['max_depth']}, "
              f"lr={p['learning_rate']}"
              f"  sharpe={r['sharpe_ratio']:.3f}  ret={r['total_return']:+.2f}%")

    # --- Tune PPO ---
    ppo_results = tune_ppo(df, train_ratio=args.train_ratio, top_k=5)
    print(f"\nTop 5 PPO configs (by val Sharpe):")
    for i, r in enumerate(ppo_results, 1):
        p = r["params"]
        print(f"  {i}. ts={p['total_timesteps']}, lr={p['learning_rate']}, "
              f"ent={p['ent_coef']}, ns={p['n_steps']}"
              f"  sharpe={r['sharpe_ratio']:.3f}  ret={r['total_return']:+.2f}%")

    # --- Tune TimesFM ---
    tfm_results = tune_timesfm(df, train_ratio=args.train_ratio, top_k=5)
    print(f"\nTop 5 TimesFM configs (by val Sharpe):")
    for i, r in enumerate(tfm_results, 1):
        p = r["params"]
        print(f"  {i}. ctx={p['context_len']}, buy_pct={p['buy_pct']}, "
              f"spread={p['strong_spread']}"
              f"  sharpe={r['sharpe_ratio']:.3f}  ret={r['total_return']:+.2f}%")

    # --- Final Evaluation ---
    best_km = km_results[0]["params"]
    best_lstm = lstm_results[0]["params"]
    best_lgbm = lgbm_results[0]["params"]
    best_ppo = ppo_results[0]["params"] if ppo_results else None
    best_tfm = tfm_results[0]["params"] if tfm_results else None

    print(f"\n{'=' * 80}")
    print("FINAL EVALUATION: Retraining best configs on full outer train set")
    print("=" * 80)

    eval_results = final_evaluation(
        df, best_km, best_lstm, best_lgbm, best_ppo, best_tfm,
        train_ratio=args.train_ratio,
    )

    print_comparison(eval_results, best_km, best_lstm, best_lgbm, best_ppo, best_tfm)

    elapsed = time.time() - t_start
    print(f"\nTotal tuning time: {elapsed:.1f}s")

    # --- Save results ---
    output = {
        "best_kmeans_params": {k: v for k, v in best_km.items() if k != "feature_cols"},
        "best_lstm_params": best_lstm,
        "best_lgbm_params": best_lgbm,
        "best_ppo_params": best_ppo,
        "best_timesfm_params": best_tfm,
        "kmeans_top5": [
            {k: v for k, v in r.items() if k != "params" or k == "params"}
            for r in km_results
        ],
        "lstm_top5": lstm_results,
        "lgbm_top5": lgbm_results,
        "ppo_top5": ppo_results,
        "timesfm_top5": tfm_results,
        "final_evaluation": eval_results,
    }
    # Convert feature_cols lists (not JSON-serializable as-is with numpy)
    for r in output["kmeans_top5"]:
        if "params" in r and "feature_cols" in r["params"]:
            r["params"]["feature_cols"] = list(r["params"]["feature_cols"])

    with open(args.output, "w") as f:
        json.dump(output, f, indent=2, default=str)
    print(f"\nResults saved to {args.output}")


if __name__ == "__main__":
    main()

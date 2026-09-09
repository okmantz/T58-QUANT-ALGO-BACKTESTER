"""Tests for app.ai.research_loop."""
from __future__ import annotations

import numpy as np
import pandas as pd
import pytest

from app.ai.ollama_settings import OllamaSettings
from app.ai.strategy_generator import GenerationResult
from app.ai import research_loop as rl
from app.backtest.risk import RiskConfig
from app.prop.simulator import PropRules


@pytest.fixture(autouse=True)
def _isolated_experiment_db(tmp_path, monkeypatch):
    """Every run_research_loop() call records into app.ai.experiment_memory
    (both the SQL row and, since research_loop's dedup check consults
    is_dna_tagset_previously_discarded, PAST records) -- isolate each
    test's database so one test's DISCARD verdicts can never leak into
    another test's dedup check."""
    from app.ai import experiment_memory
    monkeypatch.setattr(experiment_memory, "_db_path", lambda: tmp_path / "experiments.db")
    yield


def _df(n=2000, seed=1, trending=True):
    rng = np.random.default_rng(seed)
    ts = pd.date_range("2023-01-01", periods=n, freq="15min")
    if trending:
        drift = np.linspace(0, 60, n)
        noise = np.cumsum(rng.normal(0, 0.5, n))
    else:
        drift = np.zeros(n)
        noise = rng.normal(0, 0.5, n)
    price = 1900 + drift + noise
    high = price + np.abs(rng.normal(0.3, 0.15, n))
    low = price - np.abs(rng.normal(0.3, 0.15, n))
    return pd.DataFrame({
        "timestamp": ts, "open": price, "high": high, "low": low, "close": price, "volume": 100.0,
    })


_SMA_CROSS_CODE = """
import numpy as np

STOP_LOSS_PIPS = 20
TAKE_PROFIT_PIPS = 40

def generate_signals(df):
    fast = df['close'].rolling(10).mean()
    slow = df['close'].rolling(30).mean()
    signal = np.where(fast > slow, 1, np.where(fast < slow, -1, 0))
    return df['close'].__class__(signal, index=df.index)
"""

_NO_SIGNAL_CODE = """
def generate_signals(df):
    return df['close'] * 0
"""


def _settings(usable=True):
    return OllamaSettings(enabled=usable, host="http://localhost:11434", model="llama3.1")


def _rules():
    return PropRules(account_size=50_000, evaluation_profit_target_pct=8, daily_loss_limit_pct=5, max_drawdown_pct=10)


def _risk():
    return RiskConfig(initial_balance=50_000, risk_mode="percent", risk_value=1.0)


# ---------------------------------------------------------------------------
# diagnose_failure
# ---------------------------------------------------------------------------

class _FakeTrade:
    def __init__(self, entry_time, pnl):
        self.entry_time = entry_time
        self.pnl = pnl


def test_diagnose_failure_flags_low_volatility_concentration():
    df = _df(500, trending=False)
    # Make the early half of the series artificially low-volatility by
    # flattening high/low there, then concentrate losing trades in it.
    df.loc[: len(df) // 2, "high"] = df.loc[: len(df) // 2, "close"] + 0.01
    df.loc[: len(df) // 2, "low"] = df.loc[: len(df) // 2, "close"] - 0.01
    early_times = df["timestamp"].iloc[: len(df) // 2 : 5]
    trades = [_FakeTrade(t, -50.0) for t in early_times]
    diag = rl.diagnose_failure(df, trades)
    assert diag["regime"] == "low_vol"
    assert diag["low_vol_loss_pct"] >= 65.0
    assert "low-volatility" in diag["suggestion"]


def test_diagnose_failure_returns_none_suggestion_with_too_few_losers():
    df = _df(200)
    trades = [_FakeTrade(df["timestamp"].iloc[10], -50.0)]
    diag = rl.diagnose_failure(df, trades)
    assert diag["suggestion"] is None


def test_diagnose_failure_handles_no_losers_gracefully():
    df = _df(200)
    trades = [_FakeTrade(df["timestamp"].iloc[i], 50.0) for i in range(10)]
    diag = rl.diagnose_failure(df, trades)
    assert diag["suggestion"] is None


def test_diagnose_failure_always_returns_session_keys():
    """Every return path -- including the too-little-data early exits --
    must carry the session fields so callers never need to .get() them."""
    df = _df(200)
    trades = [_FakeTrade(df["timestamp"].iloc[10], -50.0)]  # too few losers for the ATR check
    diag = rl.diagnose_failure(df, trades)
    assert set(diag.keys()) >= {"session_loss_pct", "concentrated_session", "session_suggestion"}
    # With a single loser its loss is trivially 100% in whichever session
    # it fell in -- the ATR-based `suggestion` still correctly stays None
    # since that check has its own, separate 5-loser minimum.
    assert diag["suggestion"] is None


def test_diagnose_failure_flags_session_concentration():
    df = _df(500, trending=False)
    ts = pd.to_datetime(df["timestamp"])
    # Concentrate every losing trade's entry inside the fixed 00:00-07:00
    # "asia" window (see app.validation.regime_matrix._SESSION_WINDOWS).
    asia_times = ts[ts.dt.hour < 7]
    trades = [_FakeTrade(t, -50.0) for t in asia_times[:20]]
    diag = rl.diagnose_failure(df, trades)
    assert diag["concentrated_session"] == "asia"
    assert diag["session_loss_pct"]["asia"] >= 65.0
    assert "asia" in diag["session_suggestion"].lower()


# ---------------------------------------------------------------------------
# _ask_ollama_next_hypothesis (fallback path -- no network)
# ---------------------------------------------------------------------------

def test_ask_ollama_falls_back_when_not_usable():
    settings = _settings(usable=False)
    diag = {"suggestion": "Test adding an ATR-percentile entry filter."}
    idea, from_ollama = rl._ask_ollama_next_hypothesis(settings, "Original idea.", diag)
    assert from_ollama is False
    assert "Original idea." in idea
    assert "ATR-percentile" in idea


def test_ask_ollama_falls_back_to_prior_idea_when_no_suggestion():
    settings = _settings(usable=False)
    idea, from_ollama = rl._ask_ollama_next_hypothesis(settings, "Original idea.", {"suggestion": None})
    assert idea == "Original idea."
    assert from_ollama is False


# ---------------------------------------------------------------------------
# run_research_loop -- generate_strategy mocked, no real Ollama needed
# ---------------------------------------------------------------------------

def test_run_research_loop_requires_usable_ollama():
    result = rl.run_research_loop(_df(), _risk(), _rules(), _settings(usable=False))
    assert result.stopped_reason == "ollama_unavailable"
    assert result.iterations == []


def test_run_research_loop_records_keep_verdict_for_a_working_strategy(monkeypatch):
    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(code=_SMA_CROSS_CODE))
    monkeypatch.setattr(rl, "_ask_ollama_next_hypothesis", lambda *a, **k: ("next idea", False))
    cfg = rl.ResearchLoopConfig(n_iterations=1, mc_sims=50, survival_sims=100, keep_score_threshold=-1.0)
    result = rl.run_research_loop(_df(2000), _risk(), _rules(), _settings(), cfg)
    assert len(result.iterations) == 1
    it = result.iterations[0]
    assert it.verdict in ("KEEP", "DISCARD")  # depends on synthetic data, but must have run
    assert it.trades > 0
    assert it.prop_survival_score is not None
    assert result.best_iteration is it


def test_run_research_loop_marks_no_trades_as_discard(monkeypatch):
    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(code=_NO_SIGNAL_CODE))
    cfg = rl.ResearchLoopConfig(n_iterations=1)
    result = rl.run_research_loop(_df(500), _risk(), _rules(), _settings(), cfg)
    assert len(result.iterations) == 1
    assert result.iterations[0].verdict == "NO_TRADES"
    assert result.iterations[0].trades == 0


def test_run_research_loop_stops_on_generation_failure(monkeypatch):
    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(error="Ollama unreachable"))
    cfg = rl.ResearchLoopConfig(n_iterations=3)
    result = rl.run_research_loop(_df(500), _risk(), _rules(), _settings(), cfg)
    assert len(result.iterations) == 1  # breaks immediately, doesn't retry a dead connection 3 times
    assert result.iterations[0].verdict == "GENERATION_FAILED"
    assert result.stopped_reason == "GENERATION_FAILED"


def test_run_research_loop_skips_repeated_dna_signature(monkeypatch):
    # Every iteration generates the exact same code -> exact same DNA
    # signature -> after the first DISCARD, subsequent iterations must
    # be skipped as duplicates rather than re-run.
    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(code=_SMA_CROSS_CODE))
    monkeypatch.setattr(rl, "_ask_ollama_next_hypothesis", lambda *a, **k: ("same idea again", False))
    cfg = rl.ResearchLoopConfig(n_iterations=3, mc_sims=50, survival_sims=100, keep_score_threshold=999.0)  # force DISCARD
    result = rl.run_research_loop(_df(2000), _risk(), _rules(), _settings(), cfg)
    assert len(result.iterations) == 3
    verdicts = [it.verdict for it in result.iterations]
    assert verdicts[0] == "DISCARD"
    assert "SKIPPED_DUPLICATE" in verdicts[1:]


def test_research_loop_iteration_to_dict_is_plain_data():
    it = rl.ResearchLoopIteration(iteration=1, idea="x", strategy_name="s", verdict="KEEP")
    d = it.to_dict()
    assert d["iteration"] == 1
    assert d["verdict"] == "KEEP"


# ---------------------------------------------------------------------------
# Unbounded (n_iterations=None) + cancel_event -- the shape that makes this
# usable as a background/overnight companion instead of only a bounded
# interactive session.
# ---------------------------------------------------------------------------

def test_n_iterations_none_runs_until_cancelled(monkeypatch):
    import threading

    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(code=_SMA_CROSS_CODE))
    monkeypatch.setattr(rl, "_ask_ollama_next_hypothesis", lambda *a, **k: ("next idea", False))
    cfg = rl.ResearchLoopConfig(n_iterations=None, mc_sims=20, survival_sims=50, keep_score_threshold=999.0)

    cancel_event = threading.Event()
    seen = []

    def _log(msg):
        seen.append(msg)
        if len(seen) > 30:  # a handful of iterations have logged -- time to stop
            cancel_event.set()

    result = rl.run_research_loop(_df(500), _risk(), _rules(), _settings(), cfg,
                                   progress_cb=_log, cancel_event=cancel_event)
    assert result.stopped_reason == "cancelled"
    assert len(result.iterations) >= 1


def test_cancel_event_set_before_first_iteration_runs_zero_iterations(monkeypatch):
    import threading

    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(code=_SMA_CROSS_CODE))
    cfg = rl.ResearchLoopConfig(n_iterations=None, mc_sims=20, survival_sims=50)
    cancel_event = threading.Event()
    cancel_event.set()

    result = rl.run_research_loop(_df(500), _risk(), _rules(), _settings(), cfg, cancel_event=cancel_event)
    assert result.stopped_reason == "cancelled"
    assert result.iterations == []


def test_bounded_n_iterations_still_works_with_a_cancel_event_that_never_fires(monkeypatch):
    import threading

    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(code=_SMA_CROSS_CODE))
    monkeypatch.setattr(rl, "_ask_ollama_next_hypothesis", lambda *a, **k: ("next idea", False))
    cfg = rl.ResearchLoopConfig(n_iterations=2, mc_sims=20, survival_sims=50, keep_score_threshold=999.0)
    result = rl.run_research_loop(_df(500), _risk(), _rules(), _settings(), cfg, cancel_event=threading.Event())
    assert result.stopped_reason == "completed"
    assert len(result.iterations) == 2


# ---------------------------------------------------------------------------
# ResearchLoopRunner -- background-thread wrapper for use as an overnight
# companion, mirroring EvolutionRunner's start()/stop_and_wait() shape.
# ---------------------------------------------------------------------------

def test_runner_start_and_stop_and_wait(monkeypatch):
    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(code=_SMA_CROSS_CODE))
    monkeypatch.setattr(rl, "_ask_ollama_next_hypothesis", lambda *a, **k: ("next idea", False))
    cfg = rl.ResearchLoopConfig(n_iterations=None, mc_sims=20, survival_sims=50, keep_score_threshold=999.0)
    runner = rl.ResearchLoopRunner(_df(500), _risk(), _rules(), _settings(), cfg)

    runner.start()
    assert runner.is_running
    stopped = runner.stop_and_wait(timeout=15.0)
    assert stopped
    assert not runner.is_running
    assert runner.stopped_reason == "cancelled"
    assert len(runner.iterations) >= 1


def test_runner_bounded_completes_on_its_own(monkeypatch):
    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(code=_SMA_CROSS_CODE))
    monkeypatch.setattr(rl, "_ask_ollama_next_hypothesis", lambda *a, **k: ("next idea", False))
    cfg = rl.ResearchLoopConfig(n_iterations=1, mc_sims=20, survival_sims=50, keep_score_threshold=999.0)
    runner = rl.ResearchLoopRunner(_df(500), _risk(), _rules(), _settings(), cfg)

    runner.start()
    import time
    deadline = time.time() + 15.0
    while runner.is_running and time.time() < deadline:
        time.sleep(0.1)
    assert not runner.is_running
    assert runner.stopped_reason == "completed"
    assert len(runner.iterations) == 1


def test_runner_status_reports_progress(monkeypatch):
    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(code=_SMA_CROSS_CODE))
    monkeypatch.setattr(rl, "_ask_ollama_next_hypothesis", lambda *a, **k: ("next idea", False))
    cfg = rl.ResearchLoopConfig(n_iterations=1, mc_sims=20, survival_sims=50, keep_score_threshold=999.0)
    runner = rl.ResearchLoopRunner(_df(500), _risk(), _rules(), _settings(), cfg)
    runner.start()
    runner.stop_and_wait(timeout=15.0)
    status = runner.status()
    assert status["running"] is False
    assert status["n_iterations_run"] == 1


def test_on_iteration_fires_incrementally_not_only_at_the_end(monkeypatch):
    """Regression test: run_research_loop's on_iteration callback must
    fire the MOMENT each iteration completes, not only once at the very
    end via the returned ResearchLoopResult -- this is what lets
    ResearchLoopRunner (and the web status.json poll built on it) show
    live progress on an unbounded/long-running loop instead of an empty
    list until it stops."""
    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(code=_SMA_CROSS_CODE))
    monkeypatch.setattr(rl, "_ask_ollama_next_hypothesis", lambda *a, **k: ("next idea", False))
    cfg = rl.ResearchLoopConfig(n_iterations=3, mc_sims=20, survival_sims=50, keep_score_threshold=999.0)

    seen_at_callback_time = []

    def on_iteration(it):
        # Captured INSIDE the loop, before run_research_loop has returned --
        # proves the callback isn't just replaying the final list at the end.
        seen_at_callback_time.append(it.iteration)

    result = rl.run_research_loop(_df(500), _risk(), _rules(), _settings(), cfg, on_iteration=on_iteration)
    assert seen_at_callback_time == [1, 2, 3]
    assert len(result.iterations) == 3


def test_runner_iterations_populate_while_still_running(monkeypatch):
    """Direct regression test for the same bug at the ResearchLoopRunner
    level: .iterations must grow WHILE is_running is still True, not stay
    empty until the thread exits."""
    monkeypatch.setattr(rl, "generate_strategy", lambda *a, **k: GenerationResult(code=_SMA_CROSS_CODE))
    monkeypatch.setattr(rl, "_ask_ollama_next_hypothesis", lambda *a, **k: ("next idea", False))
    cfg = rl.ResearchLoopConfig(n_iterations=None, mc_sims=20, survival_sims=50, keep_score_threshold=999.0)
    runner = rl.ResearchLoopRunner(_df(500), _risk(), _rules(), _settings(), cfg)

    runner.start()
    import time
    deadline = time.time() + 10.0
    while runner.is_running and len(runner.iterations) < 1 and time.time() < deadline:
        time.sleep(0.01)
    assert runner.is_running  # still running -- we stopped waiting because iterations appeared, not because it finished
    assert len(runner.iterations) >= 1
    runner.stop_and_wait(timeout=15.0)

"""
Regression tests for critical bugs fixed on 2025-11-23.

This module tests two critical bugs:
1. Data Leakage: Technical indicators shifted with close prices
2. Bankruptcy NaN Crash: Bankruptcy returns penalty instead of NaN

Reference: CRITICAL_BUGS_ANALYSIS_2025_11_23.md
"""
import numpy as np
import pandas as pd
import pytest


# ==============================================================================
# Problem #1: Data Leakage - Technical Indicators Shift
# ==============================================================================

def test_technical_indicators_shifted_with_close():
    """
    Verify that technical indicators are shifted together with close prices.

    Bug: trading_patchnew.py shifted close by 1 step, but left indicators
    unshifted, creating temporal misalignment (look-ahead bias).

    Fix: All price-derived indicators (RSI, SMA, MACD, etc.) are now shifted
    by 1 step together with close to maintain temporal consistency.
    """
    from trading_patchnew import TradingEnv

    # Create synthetic dataframe with close prices and technical indicators
    n = 100
    df = pd.DataFrame({
        "ts_ms": np.arange(n) * 60_000,
        "open": np.linspace(100.0, 110.0, n),
        "high": np.linspace(101.0, 111.0, n),
        "low": np.linspace(99.0, 109.0, n),
        "close": np.linspace(100.0, 110.0, n),  # Linear growth
        "volume": np.ones(n) * 1000.0,
        "quote_asset_volume": np.ones(n) * 100_000.0,
        "number_of_trades": np.ones(n) * 100,
        "taker_buy_base_asset_volume": np.ones(n) * 500.0,
        "taker_buy_quote_asset_volume": np.ones(n) * 50_000.0,
        # Technical indicators (calculated from ORIGINAL close before shift)
        "rsi": np.linspace(30.0, 70.0, n),      # Linear growth
        "sma_1200": np.linspace(99.0, 109.0, n),  # Linear growth
        "sma_5040": np.linspace(98.0, 108.0, n),  # Linear growth
        "macd": np.linspace(-1.0, 1.0, n),
        "macd_signal": np.linspace(-0.5, 0.5, n),
        "momentum": np.linspace(0.0, 5.0, n),
        "atr": np.linspace(1.0, 2.0, n),
        "cci": np.linspace(-50.0, 50.0, n),
        "obv": np.linspace(1000.0, 2000.0, n),
    })

    # Store original values before TradingEnv modifies them
    original_close = df["close"].copy()
    original_rsi = df["rsi"].copy()
    original_sma_1200 = df["sma_1200"].copy()

    # Initialize TradingEnv (this will shift close and indicators)
    # Note: We need to mock some dependencies to avoid full environment setup
    try:
        env = TradingEnv(
            df=df,
            symbol="TESTUSDT",
            max_steps=50,
            initial_balance=10000.0,
            max_abs_position=1.0,
            test_mode=True,  # Disable mediator and other complex components
        )
    except Exception:
        # If TradingEnv initialization fails due to missing dependencies,
        # we can test the shift logic directly
        pytest.skip("TradingEnv initialization requires full environment setup")

    # ASSERTION 1: close should be shifted by 1
    # env.df["close"][0] should be NaN (shifted from nothing)
    # env.df["close"][1] should equal original_close[0]
    assert pd.isna(env.df["close"].iloc[0]), "close[0] should be NaN after shift(1)"
    np.testing.assert_almost_equal(
        env.df["close"].iloc[1],
        original_close.iloc[0],
        decimal=6,
        err_msg="close should be shifted by 1 step"
    )

    # ASSERTION 2: RSI should be shifted by 1 (same as close)
    assert pd.isna(env.df["rsi"].iloc[0]), "rsi[0] should be NaN after shift(1)"
    np.testing.assert_almost_equal(
        env.df["rsi"].iloc[1],
        original_rsi.iloc[0],
        decimal=6,
        err_msg="rsi should be shifted by 1 step together with close"
    )

    # ASSERTION 3: SMA should be shifted by 1 (same as close)
    assert pd.isna(env.df["sma_1200"].iloc[0]), "sma_1200[0] should be NaN after shift(1)"
    np.testing.assert_almost_equal(
        env.df["sma_1200"].iloc[1],
        original_sma_1200.iloc[0],
        decimal=6,
        err_msg="sma_1200 should be shifted by 1 step together with close"
    )

    # ASSERTION 4: All indicators should be shifted by the same amount
    # This ensures temporal consistency: close[t], rsi[t], sma[t] all refer to t-1
    for idx in range(2, 10):  # Check first 10 non-NaN values
        # close[idx] == original_close[idx-1] (shifted by 1)
        # rsi[idx] == original_rsi[idx-1] (shifted by 1)
        # Both should refer to the same original timestep
        close_shift = env.df["close"].iloc[idx] == original_close.iloc[idx - 1]
        rsi_shift = env.df["rsi"].iloc[idx] == original_rsi.iloc[idx - 1]
        assert close_shift and rsi_shift, (
            f"At index {idx}: close and rsi must be shifted by same amount. "
            f"close_shift={close_shift}, rsi_shift={rsi_shift}"
        )


def test_data_leakage_prevented():
    """
    Verify that data leakage is prevented: indicators at time t should NOT
    contain information from the original close[t], only from close[t-1].

    This test ensures the fix prevents look-ahead bias.
    """
    from trading_patchnew import TradingEnv

    n = 50
    # Create dataframe where close has a sharp spike at index 25
    close_values = np.ones(n) * 100.0
    close_values[25] = 200.0  # Sharp spike (2x increase)

    # RSI calculated from original close would show spike at index 25
    rsi_values = np.ones(n) * 50.0
    rsi_values[25] = 90.0  # RSI spike (indicates strong momentum)

    df = pd.DataFrame({
        "ts_ms": np.arange(n) * 60_000,
        "open": np.ones(n) * 100.0,
        "high": np.ones(n) * 101.0,
        "low": np.ones(n) * 99.0,
        "close": close_values,
        "volume": np.ones(n) * 1000.0,
        "quote_asset_volume": np.ones(n) * 100_000.0,
        "number_of_trades": np.ones(n) * 100,
        "taker_buy_base_asset_volume": np.ones(n) * 500.0,
        "taker_buy_quote_asset_volume": np.ones(n) * 50_000.0,
        "rsi": rsi_values,
        "sma_1200": np.ones(n) * 100.0,
    })

    try:
        env = TradingEnv(
            df=df,
            symbol="TESTUSDT",
            max_steps=30,
            initial_balance=10000.0,
            max_abs_position=1.0,
            test_mode=True,
        )
    except Exception:
        pytest.skip("TradingEnv initialization requires full environment setup")

    # KEY ASSERTION: At index 25, agent should NOT see:
    # - close[25] = 200.0 (spike)
    # - rsi[25] = 90.0 (spike indicator)
    # because this would be look-ahead bias!
    #
    # Instead, agent should see:
    # - close[25] = 100.0 (from index 24, shifted)
    # - rsi[25] = 50.0 (from index 24, shifted)
    #
    # The spike information (close=200, rsi=90) should only appear at index 26
    # (after shift by 1)

    # At index 25: NO spike (shifted data)
    np.testing.assert_almost_equal(
        env.df["close"].iloc[25],
        100.0,  # From index 24 (before spike)
        decimal=1,
        err_msg="close[25] should be 100.0 (shifted from index 24), not 200.0 (spike)"
    )
    np.testing.assert_almost_equal(
        env.df["rsi"].iloc[25],
        50.0,  # From index 24 (before spike)
        decimal=1,
        err_msg="rsi[25] should be 50.0 (shifted from index 24), not 90.0 (spike)"
    )

    # At index 26: Spike appears (shifted by 1)
    np.testing.assert_almost_equal(
        env.df["close"].iloc[26],
        200.0,  # From index 25 (spike), shifted to 26
        decimal=1,
        err_msg="close[26] should be 200.0 (spike shifted from index 25)"
    )
    np.testing.assert_almost_equal(
        env.df["rsi"].iloc[26],
        90.0,  # From index 25 (spike), shifted to 26
        decimal=1,
        err_msg="rsi[26] should be 90.0 (spike shifted from index 25)"
    )


# ==============================================================================
# Problem #2: Bankruptcy NaN Crash
# ==============================================================================

def test_bankruptcy_returns_negative_penalty_not_nan():
    """
    Verify that bankruptcy (net_worth <= 0) returns a large negative penalty
    instead of NaN, preventing training crashes.

    Bug: reward.pyx:log_return() returned NAN when net_worth <= 0, causing
    training to crash with ValueError in distributional_ppo.py GAE computation.

    Fix: log_return() now returns -10.0 (large negative penalty) for bankruptcy,
    allowing training to continue and teaching agent to avoid bankruptcy.
    """
    # We need to test the Cython function, which requires compilation
    # For now, we test the Python equivalent logic
    try:
        from reward import compute_reward  # Cython module
        import lob_state_cython
    except ImportError:
        pytest.skip("Cython modules not available, cannot test reward computation")

    # Create a mock EnvState with bankruptcy condition
    state = lob_state_cython.EnvState()
    state.net_worth = 0.0  # Bankruptcy!
    state.prev_net_worth = 1000.0
    state.use_legacy_log_reward = True  # Use log_return() for reward
    state.use_potential_shaping = False
    state.gamma = 0.99
    state.potential_shaping_coef = 0.0
    state.units = 0.0
    state.last_bar_atr = 1.0
    state.risk_aversion_variance = 0.0
    state.peak_value = 1000.0
    state.risk_aversion_drawdown = 0.0
    state.trade_frequency_penalty = 0.0
    state.last_executed_notional = 0.0
    state.spot_cost_taker_fee_bps = 10.0
    state.spot_cost_half_spread_bps = 2.0
    state.spot_cost_impact_coeff = 0.0
    state.spot_cost_impact_exponent = 1.0
    state.spot_cost_adv_quote = 100000.0
    state.turnover_penalty_coef = 0.0
    state.profit_close_bonus = 0.0
    state.loss_close_penalty = 0.0
    state.bankruptcy_penalty = 0.0

    from risk_enums import ClosedReason
    closed_reason = ClosedReason.NONE
    trades_count = 0

    # Compute reward with bankruptcy condition
    reward = compute_reward(state, closed_reason, trades_count)

    # ASSERTION 1: Reward should NOT be NaN
    assert not np.isnan(reward), (
        f"Reward should not be NaN when bankruptcy occurs! "
        f"Got: {reward}. This would cause training to crash."
    )

    # ASSERTION 2: Reward should be a large negative value (penalty)
    assert reward < -5.0, (
        f"Reward should be large negative penalty for bankruptcy. "
        f"Got: {reward}, expected < -5.0"
    )

    # ASSERTION 3: Reward should be finite
    assert np.isfinite(reward), (
        f"Reward must be finite! Got: {reward}"
    )


def test_bankruptcy_penalty_magnitude():
    """
    Verify that bankruptcy penalty is significantly larger than typical rewards,
    ensuring agent prioritizes bankruptcy avoidance.
    """
    try:
        from reward import compute_reward
        import lob_state_cython
    except ImportError:
        pytest.skip("Cython modules not available")

    # Create state for normal small loss (not bankruptcy)
    state_normal = lob_state_cython.EnvState()
    state_normal.net_worth = 990.0  # Small loss
    state_normal.prev_net_worth = 1000.0
    state_normal.use_legacy_log_reward = True
    state_normal.use_potential_shaping = False
    # ... (set other required fields)

    # Create state for bankruptcy
    state_bankruptcy = lob_state_cython.EnvState()
    state_bankruptcy.net_worth = 0.0  # Bankruptcy
    state_bankruptcy.prev_net_worth = 1000.0
    state_bankruptcy.use_legacy_log_reward = True
    state_bankruptcy.use_potential_shaping = False
    # ... (set other required fields)

    from risk_enums import ClosedReason
    closed_reason = ClosedReason.NONE

    reward_normal = compute_reward(state_normal, closed_reason, 0)
    reward_bankruptcy = compute_reward(state_bankruptcy, closed_reason, 0)

    # Bankruptcy penalty should be MUCH larger than normal loss
    # Ratio should be at least 5x (bankruptcy is catastrophic failure)
    assert abs(reward_bankruptcy) > 5 * abs(reward_normal), (
        f"Bankruptcy penalty ({reward_bankruptcy}) should be at least 5x larger "
        f"than normal loss ({reward_normal})"
    )


def test_gae_computation_does_not_crash_with_bankruptcy():
    """
    Integration test: Verify that GAE computation in distributional_ppo.py
    does not crash when bankruptcy occurs in episode.

    This tests the full pipeline: reward.pyx returns penalty → GAE computation succeeds.
    """
    from distributional_ppo import _compute_gae

    # Create synthetic rollout with bankruptcy event
    n_steps = 10
    n_envs = 1

    # Normal rewards for first 8 steps, then bankruptcy at step 9
    rewards = np.zeros((n_steps, n_envs), dtype=np.float32)
    rewards[:8, 0] = 0.01  # Normal small positive rewards
    rewards[8, 0] = -10.0  # Bankruptcy penalty (large negative)
    rewards[9, 0] = 0.0    # After bankruptcy (terminal state)

    values = np.zeros((n_steps, n_envs), dtype=np.float32)
    values[:, 0] = np.linspace(1.0, 0.1, n_steps)  # Decreasing values

    episode_starts = np.zeros((n_steps, n_envs), dtype=np.float32)
    episode_starts[0, 0] = 1.0  # Episode start at step 0
    episode_starts[9, 0] = 1.0  # Episode restart after bankruptcy at step 9

    last_values = np.array([0.0], dtype=np.float32)  # Terminal value = 0
    last_dones = np.array([True], dtype=np.float32)  # Episode done
    gamma = 0.99
    gae_lambda = 0.95

    # This should NOT crash with ValueError
    try:
        advantages, returns = _compute_gae(
            rewards=rewards,
            values=values,
            episode_starts=episode_starts,
            last_values=last_values,
            last_dones=last_dones,
            gamma=gamma,
            gae_lambda=gae_lambda,
        )
    except ValueError as e:
        if "NaN or inf" in str(e):
            pytest.fail(
                f"GAE computation crashed with NaN/inf error! This indicates "
                f"bankruptcy is still returning NaN instead of penalty. Error: {e}"
            )
        else:
            raise

    # ASSERTION: GAE computation succeeded (no exception)
    # ASSERTION: Advantages and returns are finite
    assert np.all(np.isfinite(advantages)), (
        f"Advantages contain NaN/inf: {advantages}"
    )
    assert np.all(np.isfinite(returns)), (
        f"Returns contain NaN/inf: {returns}"
    )

    # ASSERTION: Advantage at bankruptcy step should be large negative
    # (reflecting the large negative penalty)
    assert advantages[8, 0] < -5.0, (
        f"Advantage at bankruptcy step should be large negative. "
        f"Got: {advantages[8, 0]}"
    )


# ==============================================================================
# Regression Prevention - Combined Tests
# ==============================================================================

def test_no_regression_data_leakage_and_bankruptcy():
    """
    Combined regression test: Verify both fixes work together without conflicts.

    This test simulates a scenario where:
    1. Technical indicators are correctly shifted (no data leakage)
    2. Bankruptcy event occurs and returns penalty (no NaN crash)
    """
    # TODO: Implement full integration test once environment setup is available
    pytest.skip("Full integration test requires complete environment setup")


if __name__ == "__main__":
    # Run tests
    pytest.main([__file__, "-v", "-s"])

# Changelog

## [2.1.0] - 2025-11-21

### Critical Fixes

- **CRITICAL BUG #4: LSTM States NOT Reset on Episode Boundaries** (2025-11-21)
  - Fixed critical issue where LSTM hidden states persisted across episode boundaries,
    causing temporal leakage between unrelated episodes and degrading value estimation accuracy
  - Root cause: Missing reset logic in `distributional_ppo.py` rollout loop
  - Solution: Added `_reset_lstm_states_for_done_envs()` method and integrated into rollout (lines 7418-7427)
  - Files modified: `distributional_ppo.py`
  - Tests added: `tests/test_lstm_episode_boundary_reset.py` (8 comprehensive tests)
  - Impact: **CRITICAL** - Expected 5-15% improvement in value loss and policy performance
  - Models trained before 2025-11-21: **STRONGLY RECOMMENDED** to retrain for best performance
  - Reference: [CRITICAL_LSTM_RESET_FIX_REPORT.md](CRITICAL_LSTM_RESET_FIX_REPORT.md)
  - Academic reference: Hausknecht & Stone (2015) "Deep Recurrent Q-Learning for POMDPs"

- **IMPROVEMENT #2: External Features NaN → 0.0 Silent Conversion** (2025-11-21)
  - Improved NaN handling with logging capability for debugging missing data
  - Root cause: `_get_safe_float()` silently converted NaN → 0.0 without warning
  - Solution: Enhanced with `log_nan=True` parameter for debugging (mediator.py:989-1072)
  - Documentation: Enhanced obs_builder.pyx docstring (lines 7-36)
  - Files modified: `mediator.py`, `obs_builder.pyx` (comments)
  - Tests added: `tests/test_nan_handling_external_features.py` (10 tests, 9 passing, 1 skipped)
  - Impact: MEDIUM - Semantic ambiguity remains (missing data = 0.0), but now debuggable
  - Future work: Add validity flags for external features (v2.2+)
  - Reference: [NUMERICAL_ISSUES_FIX_SUMMARY.md](NUMERICAL_ISSUES_FIX_SUMMARY.md)

- **CRITICAL BUG #1: Sign Convention Mismatch in LongOnlyWrapper** (2025-11-21)
  - Fixed sign convention where negative actions (reduction signals) were clipped to zero
  - Root cause: Direct clipping instead of affine mapping lost reduction information
  - Solution: Use mapping `(action + 1.0) / 2.0` to preserve full [-1,1] signal range
  - Files modified: `wrappers/action_space.py`
  - Tests: Covered in `tests/test_critical_action_space_fixes.py` (21 tests, all passing)
  - Impact: HIGH - Policy can now properly reduce positions
  - Reference: [CRITICAL_FIXES_COMPLETE_REPORT.md](CRITICAL_FIXES_COMPLETE_REPORT.md#problem-1)

- **CRITICAL BUG #2: Position Semantics DELTA→TARGET** (2025-11-21)
  - Fixed critical position doubling bug where DELTA semantics caused 2x leverage violation
  - Root cause: `ActionProto.volume_frac` was interpreted as DELTA instead of TARGET
  - Solution: Changed semantics to TARGET position (prevents doubling)
  - Files modified: `risk_guard.py`, contract documentation
  - Tests: Covered in `tests/test_critical_action_space_fixes.py`
  - Impact: **CRITICAL** - Prevents position doubling in production (2x leverage violation)
  - Models with old DELTA semantics: **MUST** retrain
  - Reference: [CRITICAL_FIXES_COMPLETE_REPORT.md](CRITICAL_FIXES_COMPLETE_REPORT.md#problem-2)

- **CRITICAL BUG #3: Action Space Range [0,1] vs [-1,1]** (2025-11-21)
  - Fixed action space mismatch where different components used different bounds
  - Root cause: Inconsistent action space definitions across codebase
  - Solution: Unified to [-1,1] everywhere for architectural consistency
  - Files modified: Various action space components
  - Tests: Covered in `tests/test_critical_action_space_fixes.py`
  - Impact: HIGH - Prevents action clipping errors and improves training stability
  - Reference: [CRITICAL_FIXES_COMPLETE_REPORT.md](CRITICAL_FIXES_COMPLETE_REPORT.md#problem-3)

### Documentation

- **Documentation Modernization** (2025-11-21)
  - Modernized all core documentation to Version 2.1
  - Updated [CLAUDE.md](CLAUDE.md) - Main project documentation (v2.0 → v2.1)
  - Completely rewrote [README.md](README.md) - Comprehensive project overview
  - Updated [DOCS_INDEX.md](DOCS_INDEX.md) - Navigation hub with critical fixes
  - Enhanced [distributional_ppo.py](distributional_ppo.py) - Expanded class docstring (1 line → 58 lines)
  - Created [DOCUMENTATION_STATUS.md](DOCUMENTATION_STATUS.md) - Centralized status tracking (70% health score)
  - Created [DOCUMENTATION_MODERNIZATION_REPORT.md](DOCUMENTATION_MODERNIZATION_REPORT.md) - Full modernization report
  - Impact: +15% average improvement in audience coverage
  - Reference: [DOCUMENTATION_MODERNIZATION_REPORT.md](DOCUMENTATION_MODERNIZATION_REPORT.md)

### Test Coverage

- **52+ New Tests for Critical Fixes** (2025-11-21)
  - LSTM Episode Reset: 8 tests (all passing)
  - NaN Handling: 10 tests (9 passing, 1 skipped - Cython)
  - Action Space Fixes: 21 tests (all passing)
  - Stale Data Temporal Causality: 3 tests (from 2025-11-20)
  - Cross-Symbol Contamination: 4 tests (from 2025-11-20)
  - Quantile Loss Formula: 11 tests (from 2025-11-20)
  - Total: 57 new regression prevention tests
  - All critical issues now have comprehensive test coverage

### Regression Prevention

- **Added Comprehensive Checklist** (2025-11-21)
  - Created [REGRESSION_PREVENTION_CHECKLIST.md](REGRESSION_PREVENTION_CHECKLIST.md)
  - Mandatory checklist for developers before modifying critical components
  - Covers: LSTM state management, action space semantics, data integrity
  - Enforces: Running tests, reading fix reports, understanding semantics

## [Unreleased]

### Added
- **Seasonality Support**: Introduced hour-of-week seasonality multipliers to improve simulation fidelity.
  - **Required actions**:
    - Regenerate multipliers with the quick-start script.
    - Validate and update configurations before training or running simulations.
  - **Resources**:
    - [Seasonality overview](docs/seasonality.md)
    - [Quick start guide](docs/seasonality_quickstart.md)
    - [Process checklist](docs/seasonality_checklist.md)
    - [Example notebook](docs/seasonality_example.md)
    - [Migration guide](docs/seasonality_migration.md)
- **Dynamic spread builder**: Added `scripts/build_spread_seasonality.py` for generating
  hour-of-week spread profiles consumed by `slippage.dynamic`. The script
  supports custom output paths, rolling windows and warns when the source
  snapshot exceeds the configured `refresh_warn_days` threshold.
- **Fee settlement & rounding controls**: YAML-конфиги теперь содержат блоки
  `fees.rounding` и `fees.settlement` с безопасными значениями по умолчанию.
  `rounding` умеет использовать `commission_step` из биржевых фильтров и
  таблиц комиссий, а `settlement` описывает расчёт комиссий в альтернативном
  активе (например, BNB) с учётом скидок.
- **Daily turnover caps**: Added configuration fields, runtime enforcement, and
  monitoring visibility for daily USD/BPS turnover limits across per-symbol and
  portfolio aggregates. Includes persistence hooks and targeted pytest coverage
  ensuring partial/deferred execution when caps bind.

### Deprecated
- `LatencyImpl.dump_latency_multipliers` and
  `LatencyImpl.load_latency_multipliers` have been replaced by
  `dump_multipliers` and `load_multipliers`. The old names continue to work but
  emit `DeprecationWarning`. See the migration guide for details.

### Fixed
- **CRITICAL BUG #10: Temporal causality violation in stale data** (2025-11-20)
  - Fixed critical issue where stale bars were returned with PREVIOUS timestamp instead
    of CURRENT timestamp, violating temporal causality and corrupting model training
  - Root cause: `impl_offline_data.py` yielded `prev_bar` directly with old timestamp
  - Solution: Create new `Bar` with current timestamp but stale prices/volume
  - Files modified: `impl_offline_data.py`
  - Tests added: `tests/test_stale_bar_temporal_causality.py` (3 tests)
  - Impact: **CRITICAL** - Models trained with data degradation may have learned incorrect
    temporal patterns. Consider retraining if `stale_prob > 0` was used.
  - Reference: [CRITICAL_FIXES_REPORT.md](CRITICAL_FIXES_REPORT.md#problem-1-temporal-causality-violation)

- **CRITICAL BUG #11: Cross-symbol contamination in feature normalization** (2025-11-20)
  - Fixed critical issue where `shift()` applied after concatenating all symbols caused
    last row of Symbol1 to leak into first row of Symbol2, corrupting normalization stats
  - Root cause: `features_pipeline.py` applied `shift(1)` to concatenated DataFrame
  - Solution: Apply `shift()` per-symbol BEFORE concat, use `groupby()` in transform
  - Files modified: `features_pipeline.py`
  - Tests added: `tests/test_normalization_cross_symbol_contamination.py` (4 tests)
  - Impact: **CRITICAL** - Multi-symbol models may have contaminated features. Consider
    retraining if multiple symbols were used with normalization.
  - Reference: [CRITICAL_FIXES_REPORT.md](CRITICAL_FIXES_REPORT.md#problem-2-cross-symbol-contamination)

- **CRITICAL BUG #12: Inverted quantile loss formula** (2025-11-20)
  - Fixed critical mathematical error where quantile loss used `Q - T` instead of correct
    `T - Q` formula from Dabney et al. (2018), inverting asymmetric penalties
  - Root cause: `distributional_ppo.py` defaulted to legacy (incorrect) formula
  - Solution: Changed default to `_use_fixed_quantile_loss_asymmetry = True`
  - Files modified: `distributional_ppo.py`
  - Tests added: `tests/test_quantile_loss_formula_default.py` (3 tests)
  - Tests updated: `tests/test_quantile_loss_with_flag.py` (8 tests, all passing)
  - Impact: **CRITICAL** - Quantile critic models have suboptimal convergence and biased
    CVaR estimates. **STRONGLY RECOMMENDED** to retrain all quantile-based models.
  - Reference: [CRITICAL_FIXES_REPORT.md](CRITICAL_FIXES_REPORT.md#problem-3-inverted-quantile-loss)
  - Academic reference: Dabney et al. (2018) "Distributional RL with Quantile Regression"

- **Bug #9: VGS parameter tracking after model load** - Fixed critical issue where VGS
  (Variance Gradient Scaler) tracked stale parameter copies instead of actual policy
  parameters after `model.load()`, causing gradient scaling to have no effect on training
  after checkpoint restoration.
  - Root cause: VGS pickled parameter references that became stale after unpickling
  - Solution: Exclude `_parameters` from pickle state and relink via `update_parameters()`
    after load
  - Files modified: `variance_gradient_scaler.py`, `distributional_ppo.py`
  - Impact: Critical for production use of checkpointing with VGS enabled

- Ensured the explained-variance reserve path preserves training masks by
  default so no-trade windows and other zero-weight samples no longer depress
  EV metrics.

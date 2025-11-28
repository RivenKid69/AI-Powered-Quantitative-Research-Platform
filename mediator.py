from __future__ import annotations

"""
Mediator — координатор между средой, LOB/симулятором исполнения, RiskGuard и EventBus.
Держит TTL ордеров, прокидывает действия агента и обновляет портфельное состояние.

Контракт ожиданий:
- env_ref.state имеет как минимум атрибуты: units: float, cash: float, max_position: float (опционально).
- env_ref.lob (опционально): объект с методами add_limit_order, remove_order, match_market_order.
  Если отсутствует — используется _DummyLOB (ничего не делает, но не ломает пайплайн).
- ExecutionSimulator (если используется) должен предоставлять внутренний SimStepReport (см. execution_sim.py),
  а наружу для логирования и анализа использовать единые core_models.ExecReport через compat_shims/sim_adapter.
"""

from dataclasses import dataclass
from decimal import Decimal
from typing import Any, Dict, List, Tuple, Optional, TYPE_CHECKING, Mapping

if TYPE_CHECKING:
    from core_models import Order, ExecReport, Position, TradeLogRow
    from core_contracts import TradeExecutor, RiskGuards

import logging
import math
import numpy as np

from core_models import ExecReport, TradeLogRow, Side, OrderType, Liquidity, ExecStatus

logger = logging.getLogger(__name__)

# Import obs_builder for observation vector construction
try:
    from obs_builder import build_observation_vector
    _HAVE_OBS_BUILDER = True
except ImportError:
    _HAVE_OBS_BUILDER = False
from core_events import EventType, OrderEvent, FillEvent
from compat_shims import sim_report_dict_to_core_exec_reports
import event_bus as eb
from impl_latency import LatencyImpl
from core_constants import PRICE_SCALE
from utils import SignalRateLimiter
from clock import now_ms
try:
    from quantizer import Quantizer, load_filters
except Exception:  # pragma: no cover - soft dependency
    Quantizer = None  # type: ignore

    def load_filters(path: str):  # type: ignore
        return {}

try:
    from impl_quantizer import QuantizerImpl  # type: ignore
except Exception:  # pragma: no cover - optional dependency
    QuantizerImpl = None  # type: ignore

try:
    import event_bus
except Exception:
    # мягкая деградация при отсутствии event_bus
    class _Stub:
        def configure(self, *a, **k): return ""
        def log_trade(self, *a, **k): pass
        def log_risk(self, *a, **k): pass
        def flush(self): pass
        def run_dir(self): return ""
    event_bus = _Stub()  # type: ignore

from action_proto import ActionProto, ActionType
from risk_guard import RiskConfig, RiskGuard
from compat_shims import sim_report_dict_to_core_exec_reports
from core_models import as_dict
from order_shims import actionproto_to_order, legacy_decision_to_order, OrderContext

# Phase 4.1: Multi-asset execution providers
try:
    from execution_providers import (
        AssetClass,
        StatisticalSlippageProvider,
        CryptoFeeProvider,
        EquityFeeProvider,
        SlippageProvider,
        FeeProvider,
    )
    _HAVE_EXEC_PROVIDERS = True
except ImportError:
    _HAVE_EXEC_PROVIDERS = False
    AssetClass = None  # type: ignore
    StatisticalSlippageProvider = None  # type: ignore
    CryptoFeeProvider = None  # type: ignore
    EquityFeeProvider = None  # type: ignore
    SlippageProvider = None  # type: ignore
    FeeProvider = None  # type: ignore

# Phase 4.1: Trading hours adapters
try:
    from adapters.alpaca.trading_hours import AlpacaTradingHoursAdapter
    _HAVE_TRADING_HOURS = True
except ImportError:
    _HAVE_TRADING_HOURS = False
    AlpacaTradingHoursAdapter = None  # type: ignore

# ExecutionSimulator и SimStepReport (как внутренний тип отчёта, импортируемый как ExecReport)
# опциональны; при отсутствии работаем напрямую с LOB
try:
    from execution_sim import SimStepReport as ExecReport, ExecutionSimulator  # type: ignore
    _HAVE_EXEC_SIM = True
except Exception:
    ExecReport = None  # type: ignore
    ExecutionSimulator = None  # type: ignore
    _HAVE_EXEC_SIM = False


# ------------------------------ Вспомогательная заглушка LOB ------------------------------

class _DummyLOB:
    """Минималистичная заглушка для разработки без Cython."""
    _next_id: int

    def __init__(self):
        self._next_id = 1

    def add_limit_order(self, is_buy_side: bool, price_ticks: int, volume: float, timestamp: int,
                        taker_is_agent: bool = True) -> Tuple[int, int]:
        oid = self._next_id
        self._next_id += 1
        # (order_id, fake_queue_position)
        return int(oid), 0

    def remove_order(self, is_buy_side: bool, price_ticks: int, order_id: int) -> bool:
        return True

    def match_market_order(self, is_buy_side: bool, volume: float, timestamp: int,
                           taker_is_agent: bool, out_prices=None, out_volumes=None,
                           out_is_buy=None, out_is_self=None, out_ids=None, max_len: int = 0):
        # Заглушка: не исполняем, возвращаем ноль сделок и нулевую комиссию
        return 0, 0.0


# ------------------------------ Mediator ------------------------------

@dataclass
class _EnvStateView:
    units: float
    cash: float
    max_position: float = 0.0


class Mediator:
    def __init__(
        self,
        env_ref: Any,
        *,
        event_level: int = 0,
        use_exec_sim: Optional[bool] = None,
        latency_steps: int = 0,
        slip_k: float = 0.0,
        seed: int = 0,
        latency_cfg: dict | None = None,
        rate_limit: float | None = None,
        backoff_base: float | None = None,
        max_backoff: float | None = None,
    ):
        """
        env_ref — ссылка на «среду» (должна держать .state и, опционально, .lob)
        event_level — уровень логов EventBus (0/1/2)
        use_exec_sim — если None, выбираем автоматически по наличию execution_sim
        latency_steps/slip_k/seed — параметры ExecutionSimulator (если используется)
        latency_cfg — параметры модели латентности для ExecutionSimulator
        """
        self.env = env_ref
        try:
            self.event_level = int(event_level)
        except Exception:
            self.event_level = 0
        rc = getattr(env_ref, "run_config", None)

        if rate_limit is None and rc is not None:
            rate_limit = getattr(rc, "max_signals_per_sec", None)
        if backoff_base is None:
            backoff_base = getattr(rc, "backoff_base_s", 2.0) if rc is not None else 2.0
        if max_backoff is None:
            max_backoff = getattr(rc, "max_backoff_s", 60.0) if rc is not None else 60.0

        # EventBus
        try:
            event_bus.configure(level=event_level)
        except Exception:
            pass

        # RiskGuard c параметрами из env_ref (если заданы)
        self.risk = RiskGuard(
            RiskConfig(
                max_abs_position=float(getattr(env_ref, "max_abs_position", 1e12)),
                max_notional=float(getattr(env_ref, "max_notional", 2e12)),
                max_drawdown_pct=float(getattr(env_ref, "max_drawdown_pct", 1.0)),
                intrabar_dd_pct=float(getattr(env_ref, "intrabar_dd_pct", 0.30)),
                dd_window=int(getattr(env_ref, "dd_window", 500)),
                bankruptcy_cash_th=float(getattr(env_ref, "bankruptcy_cash_th", -1e12)),
            )
        )

        # LOB (реальный или заглушка)
        self.lob = getattr(env_ref, "lob", None) or _DummyLOB()

        # Rate limiter for outbound signals
        self._rate_limiter = (
            SignalRateLimiter(rate_limit, backoff_base, max_backoff)
            if rate_limit and rate_limit > 0
            else None
        )

        # Counters for signal statistics
        self.total_signals = 0
        self.delayed_signals = 0
        self.rejected_signals = 0

        # ExecutionSimulator — опционально
        if use_exec_sim is None:
            use_exec_sim = _HAVE_EXEC_SIM
        self._use_exec = bool(use_exec_sim and _HAVE_EXEC_SIM)

        if latency_cfg is None:
            if rc is not None:
                latency_cfg = getattr(rc, "latency", None)

        self._latency_impl: LatencyImpl | None = None
        if self._use_exec:
            self.exec = ExecutionSimulator(latency_steps=latency_steps, slip_k=slip_k, seed=seed)  # type: ignore
            try:
                cfg = dict(latency_cfg or {})
                cfg.setdefault(
                    "symbol",
                    str(getattr(env_ref, "symbol", getattr(env_ref, "base_symbol", ""))),
                )
                l_impl = LatencyImpl.from_dict(cfg)
                l_impl.attach_to(self.exec)
                self._latency_impl = l_impl
            except Exception:
                self._latency_impl = None
        else:
            self.exec = None
            self._latency_impl = None

        # Quantizer (shared with ExecutionSimulator)
        self.quantizer_impl = None
        self.quantizer = None
        self.enforce_ppbs = True

        def _plain_mapping(obj: Any) -> Dict[str, Any]:
            if isinstance(obj, Mapping):
                try:
                    return {str(k): v for k, v in obj.items()}
                except Exception:
                    return dict(obj)
            if hasattr(obj, "dict"):
                try:
                    data = obj.dict(exclude_unset=False)  # type: ignore[call-arg]
                except Exception:
                    data = {}
                if isinstance(data, Mapping):
                    return _plain_mapping(data)
            if hasattr(obj, "__dict__"):
                try:
                    return {
                        str(k): getattr(obj, k)
                        for k in vars(obj)
                        if not str(k).startswith("_")
                    }
                except Exception:
                    return {}
            return {}

        qcfg_raw = getattr(rc, "quantizer", None) if rc is not None else None
        qcfg: Dict[str, Any] = _plain_mapping(qcfg_raw) if qcfg_raw is not None else {}

        filters_path = str(
            qcfg.get("filters_path")
            or qcfg.get("filtersPath")
            or qcfg.get("path")
            or ""
        ).strip()

        strict_raw = qcfg.get("strict_filters")
        if strict_raw is None:
            strict_raw = qcfg.get("strict")
        strict = bool(strict_raw if strict_raw is not None else True)

        enforce_raw = qcfg.get("enforce_percent_price_by_side")
        if enforce_raw is None:
            enforce_raw = qcfg.get("enforcePercentPriceBySide")
        self.enforce_ppbs = bool(enforce_raw if enforce_raw is not None else True)

        quantizer_impl = None
        if QuantizerImpl is not None and filters_path:
            cfg_payload = dict(qcfg)
            cfg_payload.setdefault("path", filters_path)
            cfg_payload.setdefault("filters_path", filters_path)
            try:
                quantizer_impl = QuantizerImpl.from_dict(cfg_payload)
            except Exception:
                quantizer_impl = None

        self.quantizer_impl = quantizer_impl
        if quantizer_impl is not None:
            self.quantizer = getattr(quantizer_impl, "quantizer", None)
            cfg_obj = getattr(quantizer_impl, "cfg", None)
            enforce_attr = getattr(cfg_obj, "enforce_percent_price_by_side", None)
            if enforce_attr is not None:
                self.enforce_ppbs = bool(enforce_attr)
            if self._use_exec and self.exec is not None:
                attach_api = getattr(self.exec, "attach_quantizer", None)
                attached = False
                if callable(attach_api):
                    try:
                        attach_api(impl=quantizer_impl)
                        attached = True
                    except TypeError:
                        attach_api = None
                    except Exception:
                        attach_api = None
                if not attached:
                    try:
                        quantizer_impl.attach_to(self.exec)
                    except Exception:
                        pass
        else:
            if filters_path and Quantizer is not None:
                try:
                    filters, _meta = load_filters(filters_path)
                    if filters:
                        self.quantizer = Quantizer(filters, strict=strict)
                except Exception:
                    self.quantizer = None
            if self._use_exec and self.exec is not None and self.quantizer is not None:
                try:
                    self.exec.set_quantizer(self.quantizer)  # type: ignore[attr-defined]
                    setattr(self.exec, "enforce_ppbs", self.enforce_ppbs)
                    setattr(self.exec, "strict_filters", strict)
                except Exception:
                    pass

        # TTL-очередь: [(order_id, expire_ts)]
        self._ttl_queue: List[Tuple[int, int]] = []

        # Внутренние «ожидаемые» объёмы по последним операциям (для согласования с отчётом)
        self._pending_buy_volume: float = 0.0
        self._pending_sell_volume: float = 0.0
        self._context_row: Any | None = None
        self._context_row_idx: int | None = None
        self._context_timestamp: int | None = None
        self._last_signal_position: float = 0.0

        # Phase 4.1: Multi-asset execution providers
        # Initialize providers based on asset_class from run_config
        self._asset_class: str = "crypto"  # Default
        self.slippage_provider: Optional[Any] = None
        self.fee_provider: Optional[Any] = None
        self.trading_hours_adapter: Optional[Any] = None
        self._extended_hours: bool = False

        if rc is not None:
            self._asset_class = getattr(rc, "asset_class", "crypto") or "crypto"
            self._extended_hours = bool(getattr(rc, "extended_hours", False))
            data_vendor = getattr(rc, "data_vendor", None)
            self._create_providers(self._asset_class, data_vendor)

    def _create_providers(
        self,
        asset_class: str,
        data_vendor: Optional[str] = None,
    ) -> None:
        """
        Factory method to create execution providers based on asset class.

        Phase 4.1: Multi-asset support for crypto and equity.

        Args:
            asset_class: "crypto" or "equity"
            data_vendor: Optional data vendor override (e.g., "alpaca", "binance")
        """
        asset_class_lower = str(asset_class).lower()

        if not _HAVE_EXEC_PROVIDERS:
            logger.debug(
                "Mediator: execution_providers not available, "
                "using legacy slippage/fee configuration"
            )
            return

        if asset_class_lower == "equity":
            # Equity: tighter spreads, lower impact, commission-free + regulatory fees
            self.slippage_provider = StatisticalSlippageProvider(
                impact_coef=0.05,  # Lower impact for deeper equity markets
                spread_bps=2.0,    # Tighter spreads for liquid US equities
                volatility_scale=1.0,
                min_slippage_bps=0.0,
                max_slippage_bps=200.0,  # 2% max for equities
            )
            self.fee_provider = EquityFeeProvider(
                include_regulatory=True,  # SEC + TAF fees on sells
            )

            # Trading hours adapter for US equity markets
            if _HAVE_TRADING_HOURS and AlpacaTradingHoursAdapter is not None:
                try:
                    self.trading_hours_adapter = AlpacaTradingHoursAdapter(
                        config={
                            "allow_extended_hours": self._extended_hours,
                        }
                    )
                except Exception as e:
                    logger.warning(
                        "Failed to initialize AlpacaTradingHoursAdapter: %s", e
                    )
                    self.trading_hours_adapter = None

            logger.info(
                "Mediator: configured for EQUITY asset class "
                "(impact_coef=0.05, spread_bps=2.0, regulatory_fees=True, "
                "extended_hours=%s)",
                self._extended_hours,
            )

        else:
            # Crypto (default): wider spreads, higher impact, percentage fees
            self.slippage_provider = StatisticalSlippageProvider(
                impact_coef=0.1,   # Higher impact for crypto
                spread_bps=5.0,    # Wider spreads
                volatility_scale=1.0,
                min_slippage_bps=0.0,
                max_slippage_bps=500.0,  # 5% max for crypto
            )
            self.fee_provider = CryptoFeeProvider(
                maker_bps=2.0,   # 0.02% maker
                taker_bps=4.0,   # 0.04% taker
            )

            # No trading hours adapter for 24/7 crypto markets
            self.trading_hours_adapter = None

            logger.info(
                "Mediator: configured for CRYPTO asset class "
                "(impact_coef=0.1, spread_bps=5.0, maker=2bps, taker=4bps)"
            )

    def is_market_open(self, timestamp_ms: Optional[int] = None) -> bool:
        """
        Check if the market is currently open.

        Phase 4.1: For equity assets, uses trading hours adapter.
        For crypto (24/7), always returns True.

        Args:
            timestamp_ms: Unix timestamp in milliseconds. If None, uses current time.

        Returns:
            True if market is open for trading, False otherwise.
        """
        # Crypto markets are 24/7
        if self.trading_hours_adapter is None:
            return True

        # Use provided timestamp or current time
        if timestamp_ms is None:
            timestamp_ms = now_ms()

        try:
            return self.trading_hours_adapter.is_market_open(timestamp_ms)
        except Exception as e:
            logger.warning("Error checking market hours: %s", e)
            return True  # Fail open for safety

    def _check_rate_limit(self) -> bool:
        """Apply rate limiter using wall-clock milliseconds."""
        if self._rate_limiter is None:
            return True
        self.total_signals += 1
        ts_s = now_ms() / 1000.0
        allowed, status = self._rate_limiter.can_send(ts_s)
        try:
            eb.log_signal_metric(status)
        except Exception:
            pass
        if not allowed:
            if status == "delayed":
                self.delayed_signals += 1
            else:
                self.rejected_signals += 1
        return allowed

    # ------------------------------ Служебное ------------------------------

    def reset(self) -> None:
        """Очистить внутреннее состояние посредника (портфельное состояние живёт в env.state)."""
        # логируем накопленную статистику латентности за предыдущий эпизод
        self.on_episode_end()
        try:
            self.risk.reset()
        except Exception:
            pass
        self._ttl_queue.clear()
        self._pending_buy_volume = 0.0
        self._pending_sell_volume = 0.0
        self.total_signals = 0
        self.delayed_signals = 0
        self.rejected_signals = 0
        self._context_row = None
        self._context_row_idx = None
        self._context_timestamp = None
        self._last_signal_position = 0.0
        self._latest_log_ret_prev = 0.0

    def set_market_context(self, *, row: Any | None = None, row_idx: int | None = None, timestamp: int | None = None) -> None:
        """Store per-step market context passed from the environment."""
        self._context_row = row
        self._context_row_idx = int(row_idx) if row_idx is not None else None
        self._context_timestamp = int(timestamp) if timestamp is not None else None

    def on_episode_end(self) -> None:
        """Запросить и вывести статистику латентности и ограничителя сигналов."""
        if self._latency_impl is not None:
            try:
                stats = self._latency_impl.get_stats()
            except Exception:
                stats = None
            if stats:
                try:
                    event_bus.log_risk({"etype": "LATENCY_STATS", **stats})
                except Exception:
                    pass
                try:
                    self._latency_impl.reset_stats()
                except Exception:
                    pass

        # log signal rate limiter stats
        if self.total_signals > 0:
            delayed_ratio = float(self.delayed_signals) / float(self.total_signals)
            rejected_ratio = float(self.rejected_signals) / float(self.total_signals)
            try:
                event_bus.log_risk(
                    {
                        "etype": "SIGNAL_RATE_STATS",
                        "total": int(self.total_signals),
                        "delayed_ratio": delayed_ratio,
                        "rejected_ratio": rejected_ratio,
                    }
                )
            except Exception:
                pass

    def _state_view(self) -> _EnvStateView:
        st = getattr(self.env, "state", None)
        if st is None:
            # fallback: минимальный стейт
            return _EnvStateView(units=0.0, cash=0.0, max_position=0.0)
        return _EnvStateView(
            units=float(getattr(st, "units", 0.0)),
            cash=float(getattr(st, "cash", 0.0)),
            max_position=float(getattr(st, "max_position", 0.0) or 0.0),
        )

    def _normalize_trades(self, trades: list[Any]) -> list[tuple[float, float, bool, bool]]:
        """Convert heterogeneous trade payloads into (price, volume, is_buy, maker)."""
        normalized: list[tuple[float, float, bool, bool]] = []
        for trade in trades:
            price_val = getattr(trade, "price", None)
            qty_val = getattr(trade, "qty", getattr(trade, "quantity", None))
            side_flag = getattr(trade, "side", None)
            liquidity_flag = getattr(trade, "liquidity", None)
            if price_val is None or qty_val is None:
                if isinstance(trade, Mapping):
                    price_val = trade.get("price")
                    qty_val = trade.get("qty", trade.get("quantity"))
                    if side_flag is None:
                        side_flag = trade.get("side")
                    if liquidity_flag is None:
                        liquidity_flag = trade.get("liquidity")
                elif isinstance(trade, (list, tuple)) and len(trade) >= 2:
                    price_val, qty_val = trade[0], trade[1]
                    if len(trade) > 2:
                        side_flag = trade[2]
                    if len(trade) > 3:
                        liquidity_flag = trade[3]
            try:
                price_f = float(price_val)
                qty_f = float(qty_val)
            except (TypeError, ValueError):
                continue
            if not math.isfinite(price_f) or not math.isfinite(qty_f):
                continue
            side_txt = str(side_flag or "").upper()
            liquidity_txt = str(liquidity_flag or "").lower()
            is_buy = side_txt == "BUY"
            maker_flag = liquidity_txt == "maker"
            normalized.append((price_f, qty_f, is_buy, maker_flag))
        return normalized

    def _apply_trades_to_state(self, trades: List[Tuple[float, float, bool, bool]]) -> None:
        """
        Обновить env.state по списку сделок: (price, volume, is_buy, maker_is_agent).
        Buy → увеличивает units, уменьшает cash; Sell → уменьшает units, увеличивает cash.
        """
        st = getattr(self.env, "state", None)
        if st is None:
            return
        for price, vol, is_buy, _maker_is_agent in trades:
            if is_buy:
                st.units = float(st.units) + float(vol)
                st.cash = float(st.cash) - float(price) * float(vol)
            else:
                st.units = float(st.units) - float(vol)
                st.cash = float(st.cash) + float(price) * float(vol)

    def _process_ttl_queue(self, now_ts: int) -> None:
        """Отменить просроченные ордера."""
        if not self._ttl_queue:
            return
        keep: List[Tuple[int, int]] = []
        for order_id, exp_ts in self._ttl_queue:
            if now_ts >= exp_ts:
                # Нет информации о стороне/цене в очереди — отменяем «вслепую», игнорируя результат
                try:
                    self.lob.remove_order(True, 0, order_id)
                except Exception:
                    pass
                try:
                    self.lob.remove_order(False, 0, order_id)
                except Exception:
                    pass
            else:
                keep.append((order_id, exp_ts))
        self._ttl_queue = keep

    # ------------------------------ Публичный API ------------------------------

    def add_limit_order(self, *, is_buy_side: bool, price_ticks: int, volume: float,
                        timestamp: int, ttl_steps: int = 0, taker_is_agent: bool = True) -> Tuple[int, int]:
        """
        Разместить лимитный ордер напрямую в LOB.
        Возвращает (order_id, queue_position). При ttl_steps>0 — ордер будет отменён после истечения.
        """
        # pre-trade риск по ожидаемой позиции
        st = self._state_view()
        proto = ActionProto(action_type=ActionType.LIMIT, volume_frac=float(volume) / max(1.0, st.max_position))
        evt = self.risk.on_action_proposed(self.env.state, proto)  # type: ignore[attr-defined]
        if evt.name != "NONE":
            return 0, 0
        price_ticks_q = int(price_ticks)
        volume_q = float(volume)
        symbol = str(getattr(self.env, "symbol", getattr(self.env, "base_symbol", ""))).upper()
        ref_price = getattr(self.env, "last_mtm_price", getattr(self.env, "last_mid", None))
        if self.quantizer is not None:
            try:
                price_abs = float(price_ticks_q) / PRICE_SCALE
                p_abs = self.quantizer.quantize_price(symbol, price_abs)
                q = self.quantizer.quantize_qty(symbol, volume_q)
                q_clamped = self.quantizer.clamp_notional(symbol, p_abs if p_abs > 0 else (ref_price or 0.0), q)
                p_ticks = int(round(p_abs * PRICE_SCALE))
                if p_ticks != price_ticks_q or abs(q - volume_q) > 1e-12 or abs(q_clamped - q) > 1e-12:
                    return 0, 0
                if self.enforce_ppbs and ref_price is not None:
                    side = "BUY" if is_buy_side else "SELL"
                    if not self.quantizer.check_percent_price_by_side(symbol, side, p_abs, ref_price):
                        return 0, 0
                price_ticks_q = p_ticks
                volume_q = q_clamped
            except Exception:
                return 0, 0

        if not self._check_rate_limit():
            return 0, 0

        order_id, qpos = self.lob.add_limit_order(
            bool(is_buy_side),
            int(price_ticks_q),
            float(volume_q),
            int(timestamp),
            bool(taker_is_agent),
        )
        if int(ttl_steps) > 0:
            ttl_set = False
            if hasattr(self.lob, "set_order_ttl"):
                try:
                    ttl_set = bool(self.lob.set_order_ttl(int(order_id), int(ttl_steps)))
                except Exception:
                    ttl_set = False
            if not ttl_set:
                self._ttl_queue.append((int(order_id), int(timestamp) + int(ttl_steps)))
        # учёт «ожидаемого» объёма
        if is_buy_side:
            self._pending_buy_volume += float(volume_q)
        else:
            self._pending_sell_volume += float(volume_q)
        return int(order_id), int(qpos)

    def remove_order(self, *, is_buy_side: bool, price_ticks: int, order_id: int) -> bool:
        """Отменить ордер по ID и цене (грубый контракт, для реального LOB достаточно ID)."""
        ok = False
        try:
            ok = bool(self.lob.remove_order(bool(is_buy_side), int(price_ticks), int(order_id)))
        finally:
            # убрать из TTL-очереди, если там есть
            self._ttl_queue = [(oid, ts) for (oid, ts) in self._ttl_queue if oid != int(order_id)]
        return ok

    def match_market_order(self, *, is_buy_side: bool, volume: float, timestamp: int,
                           taker_is_agent: bool = True) -> List[Tuple[float, float, bool, bool]]:
        """
        Исполнить маркет-заявку через LOB.
        Возвращает список сделок [(price, volume, is_buy, maker_is_agent)].
        """
        # pre-trade риск по ожидаемой позиции
        st = self._state_view()
        proto = ActionProto(action_type=ActionType.MARKET, volume_frac=float(volume) / max(1.0, st.max_position))
        evt = self.risk.on_action_proposed(self.env.state, proto)  # type: ignore[attr-defined]
        if evt.name != "NONE":
            return []

        # Попробуем использовать Cython LOB сигнатуру (с буферами), если она доступна
        trades: List[Tuple[float, float, bool, bool]] = []
        if self._check_rate_limit():
            try:
                max_len = 1024
                prices = np.empty(max_len, dtype=np.float64)
                vols = np.empty(max_len, dtype=np.float64)
                is_buy_arr = np.empty(max_len, dtype=np.int32)
                is_self_arr = np.empty(max_len, dtype=np.int32)
                ids = np.empty(max_len, dtype=np.int64)
                n, fee_total = self.lob.match_market_order(
                    bool(is_buy_side),
                    float(volume),
                    int(timestamp),
                    bool(taker_is_agent),
                    prices,
                    vols,
                    is_buy_arr,
                    is_self_arr,
                    ids,
                    int(max_len),
                )
                for i in range(int(n)):
                    trades.append(
                        (
                            float(prices[i]),
                            float(vols[i]),
                            bool(is_buy_arr[i]),
                            bool(is_self_arr[i]),
                        )
                    )
            except Exception:
                # Заглушечный путь: ничего не исполнилось
                trades = []

        # применяем сделки к состоянию и логируем
        if trades:
            self._apply_trades_to_state(trades)
            for (px, vol, is_buy, is_self) in trades:
                try:
                    # формируем ExecReport и логируем единообразно
                    _rid = str(getattr(event_bus, "_STATE").run_id if hasattr(event_bus, "_STATE") else "")
                    _sym = str(getattr(event_bus, "_STATE").default_symbol if hasattr(event_bus, "_STATE") else "UNKNOWN")
                    _er = ExecReport(
                        ts=int(timestamp),
                        run_id=_rid,
                        symbol=_sym,
                        side=Side.BUY if bool(is_buy) else Side.SELL,
                        order_type=OrderType.MARKET,
                        price=Decimal(str(float(px))),
                        quantity=Decimal(str(float(vol))),
                        fee=Decimal("0"),
                        fee_asset=None,
                        exec_status=ExecStatus.FILLED,
                        liquidity=Liquidity.UNKNOWN,
                        client_order_id=None,
                        order_id=None,
                        trade_id=None,
                        pnl=None,
                        meta={},
                    )
                    event_bus.log_trade(_er)
                except Exception:
                    pass

        # post-trade проверки
        mid_for_risk = trades[-1][0] if trades else float(
            getattr(self.env, "last_mtm_price", getattr(self.env, "last_mid", 0.0))
        )
        try:
            self.risk.on_post_trade(self.env.state, float(mid_for_risk))  # type: ignore[attr-defined]
        except Exception:
            pass

        return trades

    def step_action(self, proto: ActionProto, *, timestamp: int) -> dict:
        """
        Унифицированная точка для выполнения действия агента.
        Возвращает краткий отчёт dict (совместим с ExecReport.to_dict при наличии execution_sim).
        """
        # локальный буфер событий
        events: list[dict] = []
        pre_cancelled: list[int] = []

        now_ts = int(timestamp)
        try:
            self._process_ttl_queue(now_ts)
        except Exception:
            pass
        try:
            if not self._use_exec:
                decay_fn = getattr(self.lob, "decay_ttl_and_cancel", None)
                if callable(decay_fn):
                    pre_cancelled = [int(x) for x in decay_fn()]
        except Exception:
            pass

        # Сформировать Order из proto (или legacy dict)
        ctx = OrderContext(
            ts_ms=int(timestamp),
            symbol=str(getattr(self.env, "symbol", "UNKNOWN")),
            ref_price=float(
                getattr(self.env, "last_mtm_price", getattr(self.env, "last_mid", 0.0))
            )
            if hasattr(self.env, "last_mtm_price") or hasattr(self.env, "last_mid")
            else None,
            max_position_abs_base=float(getattr(getattr(self.env, "state", None), "max_position", 0.0) or getattr(self.env, "max_abs_position", 0.0) or 0.0),
            tick_size=None,  # квантование делается ниже по контуру
            price_offset_ticks=int(getattr(proto, "price_offset_ticks", 0)),
            tif=str(getattr(proto, "tif", "GTC")),
            client_tag=str(getattr(proto, "client_tag", "") or ""),
        )

        order_obj: Order | None = None
        try:
            # Если это ActionProto
            order_obj = actionproto_to_order(proto, ctx)
        except Exception:
            # Если пришёл legacy dict
            if isinstance(proto, dict):
                order_obj = legacy_decision_to_order(proto, ctx)

        # публикация факта подачи действия
        try:
            submitted_event = OrderEvent(
                etype=EventType.ORDER_SUBMITTED,
                ts=int(timestamp),
                order=(order_obj.to_dict() if hasattr(order_obj, "to_dict") else None),
                meta={"action": getattr(proto, "to_dict", lambda: {"type": int(getattr(proto, "action_type", 0))})()}
            ).to_dict()
            events.append(submitted_event)
        except Exception:
            pass

        # pre-trade
        evt = self.risk.on_action_proposed(self.env.state, proto)  # type: ignore[attr-defined]
        info: dict = {}
        if evt.name != "NONE":
            info["risk_event"] = evt.name
            return {"trades": [], "cancelled_ids": [], "new_order_ids": [], "fee_total": 0.0,
                    "new_order_pos": [], "info": info, "events": events}

        # если есть ExecutionSimulator — используем его
        if self._use_exec and self.exec is not None:
            if proto.action_type != ActionType.HOLD and not self._check_rate_limit():
                info["rate_limited"] = True
                return {"trades": [], "cancelled_ids": [], "new_order_ids": [], "fee_total": 0.0,
                        "new_order_pos": [], "info": info, "events": events}
            try:
                bid = getattr(self.env, "last_bid", None)
                ask = getattr(self.env, "last_ask", None)
                try:
                    self.exec.set_market_snapshot(bid=bid, ask=ask)  # type: ignore[union-attr]
                except Exception:
                    pass
                mid = None
                if bid is not None and ask is not None:
                    mid = (float(bid) + float(ask)) / 2.0
                else:
                    mid = getattr(
                        self.env, "last_mtm_price", getattr(self.env, "last_mid", None)
                    )
                try:
                    if mid is not None:
                        self.exec.set_ref_price(float(mid))  # type: ignore[union-attr]
                except Exception:
                    pass
                cli_id = self.exec.submit(proto)  # type: ignore[union-attr]
                # в простом варианте считаем, что latency=0 и сразу «поп» (если latency>0 — поп произойдёт на тик)
                report: ExecReport = self.exec.pop_ready()  # type: ignore  # ExecReport — это alias на SimStepReport
                try:
                    setattr(
                        self.env,
                        "last_bid",
                        float(getattr(report, "bid", getattr(self.env, "last_bid", 0.0))),
                    )
                    setattr(
                        self.env,
                        "last_ask",
                        float(getattr(report, "ask", getattr(self.env, "last_ask", 0.0))),
                    )
                    mtm = float(
                        getattr(
                            report,
                            "mtm_price",
                            getattr(
                                self.env,
                                "last_mtm_price",
                                getattr(self.env, "last_mid", 0.0),
                            ),
                        )
                    )
                    setattr(self.env, "last_mtm_price", mtm)
                    setattr(self.env, "last_mid", mtm)
                except Exception:
                    pass
                # применить и пост-проверки
                raw_trades = list(getattr(report, "trades", []))
                simple_trades = self._normalize_trades(raw_trades)
                self._apply_trades_to_state(simple_trades)
                mid_for_risk = float(
                    getattr(
                        report,
                        "mtm_price",
                        getattr(
                            self.env,
                            "last_mtm_price",
                            getattr(self.env, "last_mid", 0.0),
                        ),
                    )
                )
                self.risk.on_post_trade(self.env.state, mid_for_risk)  # type: ignore[attr-defined]
                d = report.to_dict()
                try:
                    exec_reports = sim_report_dict_to_core_exec_reports(
                        d,
                        symbol=str(getattr(self.env, "symbol", getattr(self.env, "base_symbol", "UNKNOWN"))),
                        client_order_id=None
                    )
                    d["core_exec_reports"] = [as_dict(er) for er in exec_reports]

                    # добавлено: публикация FillEvent и запись в unified CSV
                    try:
                        lvl = int(getattr(self, "event_level", 0))
                    except Exception:
                        lvl = 0
                    for _er in exec_reports:
                        if lvl >= 2:
                            try:
                                events.append(FillEvent(etype=EventType.EXEC_FILLED, ts=_er.ts, exec_report=_er).to_dict())
                            except Exception:
                                pass
                        # лог в unified-CSV
                        try:
                            run_id_val = getattr(event_bus, "_STATE").run_id if hasattr(event_bus, "_STATE") else ""
                            symbol_val = getattr(self.env, "symbol", getattr(self.env, "base_symbol", "UNKNOWN"))
                            event_bus.log_trade(_er)
                        except Exception:
                            pass
                except Exception:
                    d["core_exec_reports"] = []

                # возвращаем также события
                d["events"] = events
                d["info"] = info
                d["trades"] = simple_trades
                return d
            except Exception:
                # запасной путь — выполнить напрямую по типу действия
                pass

        # иначе — прямое исполнение через LOB
        trades: List[Tuple[float, float, bool, bool]] = []
        new_order_ids: List[int] = []
        new_order_pos: List[int] = []
        cancelled_ids: List[int] = list(pre_cancelled)
        fee_total: float = 0.0

        if proto.action_type == ActionType.HOLD:
            pass
        elif proto.action_type == ActionType.MARKET:
            trades = self.match_market_order(is_buy_side=(proto.volume_frac > 0.0),
                                             volume=abs(proto.volume_frac) * max(1.0, self._state_view().max_position),
                                             timestamp=int(timestamp), taker_is_agent=True)
        elif proto.action_type == ActionType.LIMIT:
            ttl_steps = int(getattr(proto, "ttl_steps", 0))
            vol = abs(proto.volume_frac) * max(1.0, self._state_view().max_position)
            price_ticks = int(getattr(proto, "price_offset_ticks", 0))
            abs_price = getattr(proto, "abs_price", None)
            if abs_price is not None:
                symbol = str(getattr(self.env, "symbol", getattr(self.env, "base_symbol", ""))).upper()
                if self.quantizer is not None:
                    p_abs = self.quantizer.quantize_price(symbol, float(abs_price))
                else:
                    p_abs = float(abs_price)
                price_ticks = int(round(p_abs * PRICE_SCALE))
            oid, qpos = self.add_limit_order(is_buy_side=(proto.volume_frac > 0.0),
                                             price_ticks=price_ticks, volume=vol,
                                             timestamp=int(timestamp), ttl_steps=ttl_steps, taker_is_agent=True)
            if oid:
                new_order_ids.append(int(oid))
                new_order_pos.append(int(qpos))

        # пост-проверки и отчёт
        mid_for_risk = trades[-1][0] if trades else float(
            getattr(self.env, "last_mtm_price", getattr(self.env, "last_mid", 0.0))
        )
        try:
            self.risk.on_post_trade(self.env.state, float(mid_for_risk))  # type: ignore[attr-defined]
        except Exception:
            pass

        for (px, vol, is_buy, is_self) in trades:
            try:
                # формируем ExecReport и логируем единообразно
                _rid = str(getattr(event_bus, "_STATE").run_id if hasattr(event_bus, "_STATE") else "")
                _sym = str(getattr(event_bus, "_STATE").default_symbol if hasattr(event_bus, "_STATE") else "UNKNOWN")
                _er = ExecReport(
                    ts=int(timestamp),
                    run_id=_rid,
                    symbol=_sym,
                    side=Side.BUY if bool(is_buy) else Side.SELL,
                    order_type=OrderType.MARKET,
                    price=Decimal(str(float(px))),
                    quantity=Decimal(str(float(vol))),
                    fee=Decimal("0"),
                    fee_asset=None,
                    exec_status=ExecStatus.FILLED,
                    liquidity=Liquidity.UNKNOWN,
                    client_order_id=None,
                    order_id=None,
                    trade_id=None,
                    pnl=None,
                    meta={},
                )
                event_bus.log_trade(_er)
            except Exception:
                pass

        return {
            "trades": trades,
            "cancelled_ids": cancelled_ids,
            "new_order_ids": new_order_ids,
            "fee_total": float(fee_total),
            "new_order_pos": new_order_pos,
            "info": info,
            "events": events,
        }

    @staticmethod
    def _coerce_finite(value: Any, default: float = 0.0) -> float:
        """Cast ``value`` to ``float`` returning ``default`` when non‑finite."""

        if value is None:
            return float(default)
        try:
            numeric = float(value)
        except (TypeError, ValueError):
            return float(default)
        if not math.isfinite(numeric):
            return float(default)
        return numeric

    @staticmethod
    def _validate_critical_price(value: Any, param_name: str = "price") -> float:
        """
        Validate critical price parameter with strict requirements.

        This function enforces strict validation for price parameters where 0.0 is NOT
        an acceptable fallback. Used for mark_price, prev_price, and other critical
        price values that must be positive and finite.

        Args:
            value: The price value to validate
            param_name: Parameter name for error messages

        Returns:
            float: Validated price value (guaranteed to be positive and finite)

        Raises:
            ValueError: If price is None, NaN, Inf, or <= 0

        Best practices:
        - Financial data standards require positive, finite prices
        - Zero/negative prices indicate data corruption, not "no price"
        - NaN/Inf indicate upstream calculation errors that must be fixed
        - Fail-fast approach prevents silent data corruption

        References:
        - "Best Practices for Ensuring Financial Data Accuracy" (Paystand)
        - "Investment Model Validation" (CFA Institute)
        - "Training ML Models with Financial Data" (EODHD)
        """
        if value is None:
            raise ValueError(
                f"Invalid {param_name}: None. "
                f"Price parameters cannot be None. "
                f"This indicates missing data in the pipeline. "
                f"Check data source and ensure price is provided."
            )

        try:
            numeric = float(value)
        except (TypeError, ValueError) as e:
            raise ValueError(
                f"Invalid {param_name}: cannot convert {type(value).__name__} to float. "
                f"Price must be a numeric value. "
                f"Original error: {e}"
            )

        if math.isnan(numeric):
            raise ValueError(
                f"Invalid {param_name}: NaN (Not a Number). "
                f"This indicates missing or corrupted market data. "
                f"NaN prices cannot be safely defaulted to 0.0. "
                f"Fix data source to provide valid prices."
            )

        if math.isinf(numeric):
            sign = "positive" if numeric > 0 else "negative"
            raise ValueError(
                f"Invalid {param_name}: {sign} infinity. "
                f"This indicates arithmetic overflow in calculations. "
                f"Check price calculations for numerical stability. "
                f"Infinity prices cannot be safely handled."
            )

        if numeric <= 0.0:
            raise ValueError(
                f"Invalid {param_name}: {numeric:.10f}. "
                f"Price must be strictly positive (> 0). "
                f"Zero or negative prices are invalid in trading systems. "
                f"If this is intentional (e.g., testing), use a small positive value like 0.01."
            )

        return numeric

    @staticmethod
    def _get_safe_float(
        row: Any,
        col: str,
        default: float = 0.0,
        min_value: float = None,
        max_value: float = None,
        log_nan: bool = False
    ) -> float:
        """
        Safely extract float value from row with fallback and range validation.

        ISSUE #2 FIX: Added explicit NaN handling and optional logging to make
        silent NaN→default conversion visible for debugging.

        Args:
            row: Data row to extract from
            col: Column name
            default: Default value if extraction fails or value is NaN/Inf
            min_value: Minimum allowed value (inclusive). If result < min_value, returns default
            max_value: Maximum allowed value (inclusive). If result > max_value, returns default
            log_nan: If True, log warning when NaN/Inf is encountered (useful for debugging)

        Returns:
            Extracted float value or default if invalid/out of range

        Validates:
        - Not None
        - Can convert to float
        - Is finite (not NaN/Inf) - CRITICAL: NaN is converted to `default`
        - Within [min_value, max_value] range if specified

        Design Note (Issue #2):
            This function converts NaN to `default` (typically 0.0) to prevent NaN propagation
            through the network. This creates semantic ambiguity where "missing data" and
            "zero value" are indistinguishable to the model.

            Future Enhancement: Add validity flags (similar to ma5_valid, rsi_valid) for
            external features to explicitly signal missing data. This would require:
            - Returning tuple (value, is_valid)
            - Expanding observation space by +21 features (validity flags)
            - Retraining all models

        Examples:
        - volume = _get_safe_float(row, "volume", 1.0, min_value=0.0)  # Ensures >= 0
        - price = _get_safe_float(row, "price", 50000.0, min_value=0.01, max_value=1e9)
        - cvd = _get_safe_float(row, "cvd_24h", 0.0, log_nan=True)  # Log if NaN
        """
        if row is None:
            return default
        try:
            val = row.get(col) if hasattr(row, "get") else getattr(row, col, None)
            if val is None:
                if log_nan:
                    logger.debug(f"Feature '{col}' is None, using default={default}")
                return default
            result = float(val)
            if not math.isfinite(result):
                if log_nan:
                    logger.warning(
                        f"Feature '{col}' has non-finite value ({result}), "
                        f"using default={default}. This causes ambiguity: "
                        f"model cannot distinguish missing data from zero values."
                    )
                return default
            # Range validation
            if min_value is not None and result < min_value:
                if log_nan:
                    logger.debug(
                        f"Feature '{col}' value {result} < min_value {min_value}, "
                        f"using default={default}"
                    )
                return default
            if max_value is not None and result > max_value:
                if log_nan:
                    logger.debug(
                        f"Feature '{col}' value {result} > max_value {max_value}, "
                        f"using default={default}"
                    )
                return default
            return result
        except (TypeError, ValueError, KeyError, AttributeError) as e:
            if log_nan:
                logger.debug(f"Feature '{col}' extraction failed: {e}, using default={default}")
            return default

    @staticmethod
    def _get_safe_float_with_validity(
        row: Any,
        col: str,
        default: float = 0.0,
        min_value: float = None,
        max_value: float = None
    ) -> tuple[float, bool]:
        """
        Safely extract float value with explicit validity flag.

        ISSUE #2 FIX (COMPLETE): This method replaces silent NaN→default conversion
        with explicit validity tracking, enabling model to distinguish missing data
        from zero values.

        Args:
            row: Data row to extract from
            col: Column name
            default: Default value if extraction fails or value is NaN/Inf
            min_value: Minimum allowed value (inclusive). If result < min_value, returns (default, False)
            max_value: Maximum allowed value (inclusive). If result > max_value, returns (default, False)

        Returns:
            (value, is_valid) tuple where:
            - value: Extracted float or default if invalid/out of range
            - is_valid: True if original value was finite and within range, False otherwise

        Validates:
        - Not None → is_valid=False
        - Can convert to float → is_valid=False if fails
        - Is finite (not NaN/Inf) → is_valid=False if not finite
        - Within [min_value, max_value] range → is_valid=False if out of range

        Design Note (Issue #2 COMPLETE FIX):
            Unlike _get_safe_float() which silently converts NaN→default, this method
            returns explicit validity flag. This enables:
            1. Model can learn to distinguish "missing data" (is_valid=False) from "zero value" (is_valid=True, value=0.0)
            2. Robustness to data quality issues (API downtime, stale data, etc.)
            3. Consistent with technical indicators (ma5_valid, rsi_valid, etc.)

        Examples:
        - volume, is_valid = _get_safe_float_with_validity(row, "volume", 1.0, min_value=0.0)
        - price, is_valid = _get_safe_float_with_validity(row, "price", 50000.0, min_value=0.01, max_value=1e9)
        - cvd, is_valid = _get_safe_float_with_validity(row, "cvd_24h", 0.0)
          # is_valid=True: cvd=0.0 means balanced volume
          # is_valid=False: cvd=0.0 means missing data
        """
        if row is None:
            return (default, False)

        try:
            val = row.get(col) if hasattr(row, "get") else getattr(row, col, None)
            if val is None:
                return (default, False)

            result = float(val)

            # Check finite (NaN/Inf → invalid)
            if not math.isfinite(result):
                return (default, False)

            # Range validation
            if min_value is not None and result < min_value:
                return (default, False)
            if max_value is not None and result > max_value:
                return (default, False)

            # All checks passed - value is valid!
            return (result, True)

        except (TypeError, ValueError, KeyError, AttributeError):
            return (default, False)

    def _extract_market_data(self, row: Any, state: Any, mark_price: float, prev_price: float) -> Dict[str, float]:
        """
        Extract basic market data from row.

        CRITICAL: Uses strict validation for price parameters.
        - mark_price and prev_price MUST be positive and finite
        - Will raise ValueError if invalid (fail-fast approach)
        - No fallback to 0.0 for prices (would corrupt observations)

        Volume validation strategy:
        - P0: Raw volume data validated by _get_safe_float with min_value=0.0
          (ensures volume >= 0, prevents negative values that cause log1p(x<-1) → NaN)
        - P2: Final validation at obs_builder.pyx wrapper before writing to observation
        """
        # CRITICAL: Strict validation for prices (no fallback to 0.0)
        price = self._validate_critical_price(mark_price, param_name="mark_price")
        prev = self._validate_critical_price(prev_price, param_name="prev_price")

        # Volume normalization (adapted for 4h timeframe)
        # 4h bars aggregate ~240x more volume than 1h bars, so we use 240e6 divisor
        # CRITICAL: min_value=0.0 ensures volume >= 0, preventing log1p domain errors
        volume = self._get_safe_float(row, "volume", 1.0, min_value=0.0)
        quote_volume = self._get_safe_float(row, "quote_asset_volume", 1.0, min_value=0.0)

        # Compute normalized volume metrics
        # With volume >= 0 guaranteed by P0, tanh(log1p(x)) always yields finite result in [-1, 1]
        log_volume_norm = 0.0
        if quote_volume > 0:
            log_volume_norm = float(np.tanh(np.log1p(quote_volume / 240e6)))

        rel_volume = 0.0
        if volume > 0:
            rel_volume = float(np.tanh(np.log1p(volume / 24000.0)))

        return {
            "price": price,
            "prev_price": prev,
            "log_volume_norm": log_volume_norm,
            "rel_volume": rel_volume,
        }

    def _extract_technical_indicators(self, row: Any, sim: Any, row_idx: int) -> Dict[str, float]:
        """Extract technical indicators from row or simulator."""
        # Try to get from row first (from prepare_and_run.py features)
        # For 4h timeframe: transformers.py creates SMA names in MINUTES (not bars)
        # sma_1200 = 5 bars × 240 min/bar = 1200 minutes = 20 hours (short-term MA)
        ma5 = self._get_safe_float(row, "sma_1200", float('nan'))
        # NOTE: For 4h timeframe using sma_5040 (21 bars = 84h ≈ 3.5 days, weekly trend)
        # config_4h_timeframe.py specifies SMA_LOOKBACKS = [5, 21, 50] bars → [1200, 5040, 12000] minutes
        # HISTORICAL NAMING: Variable named "ma20" for feature schema compatibility (see feature_config.py).
        # Actual value is 21-bar SMA. Renaming would break feature parity and trained models.
        ma20 = self._get_safe_float(row, "sma_5040", float('nan'))
        rsi14 = self._get_safe_float(row, "rsi", 50.0)

        # For MACD and other indicators, try from simulator if available
        macd = 0.0
        macd_signal = 0.0
        momentum = 0.0
        atr = 0.0
        cci = 0.0
        obv = 0.0
        bb_lower = float('nan')
        bb_upper = float('nan')

        # Try to get from MarketSimulator if available
        if sim is not None and hasattr(sim, "get_macd"):
            try:
                if hasattr(sim, "get_macd"):
                    macd = float(sim.get_macd(row_idx))
                if hasattr(sim, "get_macd_signal"):
                    macd_signal = float(sim.get_macd_signal(row_idx))
                if hasattr(sim, "get_momentum"):
                    momentum = float(sim.get_momentum(row_idx))
                if hasattr(sim, "get_atr"):
                    atr = float(sim.get_atr(row_idx))
                if hasattr(sim, "get_cci"):
                    cci = float(sim.get_cci(row_idx))
                if hasattr(sim, "get_obv"):
                    obv = float(sim.get_obv(row_idx))
                if hasattr(sim, "get_bb_lower"):
                    bb_lower = float(sim.get_bb_lower(row_idx))
                if hasattr(sim, "get_bb_upper"):
                    bb_upper = float(sim.get_bb_upper(row_idx))
            except Exception:
                pass

        return {
            "ma5": ma5,
            "ma20": ma20,
            "rsi14": rsi14,
            "macd": macd,
            "macd_signal": macd_signal,
            "momentum": momentum,
            "atr": atr,
            "cci": cci,
            "obv": obv,
            "bb_lower": bb_lower,
            "bb_upper": bb_upper,
        }

    def _extract_norm_cols(self, row: Any) -> tuple[np.ndarray, np.ndarray]:
        """Extract normalized columns for external features WITH validity flags.

        ISSUE #2 FIX (COMPLETE): Now returns (values, validity) tuple to enable
        model to distinguish missing data from zero values.

        Adapted for 4h timeframe:
        - GARCH windows: 200h/14d/30d (50/84/180 bars) instead of 500m/12h/24h
        - Returns: 4h/12h/24h (1/3/6 bars) instead of 5m/15m/60m
        - SMA: sma_12000 (50 bars = 12000 минут = 200h) instead of sma_60 (60 minutes)
        - Taker Buy Ratio Momentum: 4h/8h/12h (1/2/3 bars) instead of 1h

        АРХИТЕКТУРНОЕ РЕШЕНИЕ: EXT_NORM_DIM = 28 (Phase 5 expansion)
        - Indices 0-20: Original crypto features (cvd, garch, yang_zhang, returns, taker_buy_ratio)
        - Indices 21-27: NEW stock-specific features (backward compatible)
          [21] vix_normalized     - VIX index value (normalized via tanh)
          [22] vix_regime         - VIX regime indicator (0-1 scale)
          [23] market_regime      - Bull/Bear/Sideways indicator (-1 to 1)
          [24] rs_spy_20d         - 20-day relative strength vs SPY
          [25] rs_spy_50d         - 50-day relative strength vs SPY
          [26] rs_qqq_20d         - 20-day relative strength vs QQQ
          [27] sector_momentum    - Sector momentum relative to market

        Backward Compatibility:
        - Crypto data won't have stock features → validity flags = False
        - Default values are sensible (0.0)
        - No changes to existing crypto observation building

        Returns:
            values: (35,) float32 array - feature values (NaN→0.0 fallback)
            validity: (35,) bool array - True if feature was valid, False if NaN/Inf/None
        """
        norm_cols_values = np.zeros(35, dtype=np.float32)
        norm_cols_validity = np.zeros(35, dtype=bool)  # Default to invalid for all

        # =======================================================================
        # INDICES 0-20: ORIGINAL CRYPTO FEATURES (unchanged)
        # =======================================================================

        # Map technical indicators from prepare_and_run.py to norm_cols
        # Original 8 features (adapted for 4h)
        norm_cols_values[0], norm_cols_validity[0] = self._get_safe_float_with_validity(row, "cvd_24h", 0.0)
        norm_cols_values[1], norm_cols_validity[1] = self._get_safe_float_with_validity(row, "cvd_7d", 0.0)  # 10080 минут = 7 дней
        norm_cols_values[2], norm_cols_validity[2] = self._get_safe_float_with_validity(row, "yang_zhang_48h", 0.0)  # 12 bars = 48h
        norm_cols_values[3], norm_cols_validity[3] = self._get_safe_float_with_validity(row, "yang_zhang_7d", 0.0)  # 10080 минут = 7 дней
        norm_cols_values[4], norm_cols_validity[4] = self._get_safe_float_with_validity(row, "garch_200h", 0.0)  # 50 bars = 12000 min = 200h (минимум для GARCH на 4h)
        norm_cols_values[5], norm_cols_validity[5] = self._get_safe_float_with_validity(row, "garch_14d", 0.0)  # 84 bars = 14 days
        norm_cols_values[6], norm_cols_validity[6] = self._get_safe_float_with_validity(row, "ret_12h", 0.0)  # 3 bars
        norm_cols_values[7], norm_cols_validity[7] = self._get_safe_float_with_validity(row, "ret_24h", 0.0)  # 6 bars

        # Additional 8 features for complete coverage (43 -> 51) - adapted for 4h
        norm_cols_values[8], norm_cols_validity[8] = self._get_safe_float_with_validity(row, "ret_4h", 0.0)  # 1 bar
        norm_cols_values[9], norm_cols_validity[9] = self._get_safe_float_with_validity(row, "sma_12000", 0.0)  # 50 bars = 12000 минут = 200h
        norm_cols_values[10], norm_cols_validity[10] = self._get_safe_float_with_validity(row, "yang_zhang_30d", 0.0)  # 43200 минут = 30 дней
        norm_cols_values[11], norm_cols_validity[11] = self._get_safe_float_with_validity(row, "parkinson_48h", 0.0)  # 12 bars = 48h
        norm_cols_values[12], norm_cols_validity[12] = self._get_safe_float_with_validity(row, "parkinson_7d", 0.0)  # 10080 минут = 7 дней
        norm_cols_values[13], norm_cols_validity[13] = self._get_safe_float_with_validity(row, "garch_30d", 0.0)  # 180 bars = 30 days
        norm_cols_values[14], norm_cols_validity[14] = self._get_safe_float_with_validity(row, "taker_buy_ratio", 0.0)
        norm_cols_values[15], norm_cols_validity[15] = self._get_safe_float_with_validity(row, "taker_buy_ratio_sma_24h", 0.0)  # 6 bars

        # Additional 5 features for complete taker_buy_ratio coverage
        norm_cols_values[16], norm_cols_validity[16] = self._get_safe_float_with_validity(row, "taker_buy_ratio_sma_8h", 0.0)  # 2 bars
        norm_cols_values[17], norm_cols_validity[17] = self._get_safe_float_with_validity(row, "taker_buy_ratio_sma_16h", 0.0)  # 4 bars
        norm_cols_values[18], norm_cols_validity[18] = self._get_safe_float_with_validity(row, "taker_buy_ratio_momentum_4h", 0.0)  # 1 bar
        norm_cols_values[19], norm_cols_validity[19] = self._get_safe_float_with_validity(row, "taker_buy_ratio_momentum_8h", 0.0)  # 2 bars
        norm_cols_values[20], norm_cols_validity[20] = self._get_safe_float_with_validity(row, "taker_buy_ratio_momentum_12h", 0.0)  # 3 bars

        # =======================================================================
        # INDICES 21-27: STOCK-SPECIFIC FEATURES (Phase 5 - 2025-11-27)
        # =======================================================================
        # These features are analogous to Fear & Greed for crypto.
        # For crypto data, these columns won't exist → validity=False (default)
        # This maintains 100% backward compatibility.

        # [21] VIX normalized value (tanh transformation applied in stock_features.py)
        # Range: approximately [-1, 1], centered at VIX=20
        norm_cols_values[21], norm_cols_validity[21] = self._get_safe_float_with_validity(
            row, "vix_normalized", 0.0, min_value=-3.0, max_value=3.0
        )

        # [22] VIX regime (0-1 scale: 0=low/complacency, 0.5=normal, 1=extreme fear)
        norm_cols_values[22], norm_cols_validity[22] = self._get_safe_float_with_validity(
            row, "vix_regime", 0.5, min_value=0.0, max_value=1.0
        )

        # [23] Market regime (-1=bear, 0=sideways, 1=bull)
        # Based on SPY SMA crossover and VIX level
        norm_cols_values[23], norm_cols_validity[23] = self._get_safe_float_with_validity(
            row, "market_regime", 0.0, min_value=-1.0, max_value=1.0
        )

        # [24] Relative strength vs SPY (20-day)
        # Normalized via tanh, approximately [-1, 1]
        norm_cols_values[24], norm_cols_validity[24] = self._get_safe_float_with_validity(
            row, "rs_spy_20d", 0.0, min_value=-3.0, max_value=3.0
        )

        # [25] Relative strength vs SPY (50-day)
        norm_cols_values[25], norm_cols_validity[25] = self._get_safe_float_with_validity(
            row, "rs_spy_50d", 0.0, min_value=-3.0, max_value=3.0
        )

        # [26] Relative strength vs QQQ (20-day)
        norm_cols_values[26], norm_cols_validity[26] = self._get_safe_float_with_validity(
            row, "rs_qqq_20d", 0.0, min_value=-3.0, max_value=3.0
        )

        # [27] Sector momentum relative to market
        # Normalized via tanh, approximately [-1, 1]
        norm_cols_values[27], norm_cols_validity[27] = self._get_safe_float_with_validity(
            row, "sector_momentum", 0.0, min_value=-3.0, max_value=3.0
        )

        # =======================================================================
        # INDICES 28-34: MACRO & CORPORATE FEATURES (Phase 6 - 2025-11-28)
        # =======================================================================
        # These features provide macro context and corporate event awareness.
        # For crypto data, these columns won't exist → validity=False (default)

        # [28] Dollar Index (DXY) normalized
        # DXY typically ranges 90-110, center at 100
        dxy_raw, dxy_valid = self._get_safe_float_with_validity(row, "dxy_value", 100.0)
        if dxy_valid:
            # Normalize: (DXY - 100) / 10, then tanh
            norm_cols_values[28] = float(np.tanh((dxy_raw - 100.0) / 10.0))
        else:
            norm_cols_values[28] = 0.0
        norm_cols_validity[28] = dxy_valid

        # [29] 10-Year Treasury Yield (normalized)
        # Typical range 2-5%, normalize to [-1, 1] range
        treasury_raw, treasury_valid = self._get_safe_float_with_validity(row, "treasury_10y_yield", 3.0)
        if treasury_valid:
            # Normalize: (yield - 3.5) / 2.0, then tanh
            norm_cols_values[29] = float(np.tanh((treasury_raw - 3.5) / 2.0))
        else:
            norm_cols_values[29] = 0.0
        norm_cols_validity[29] = treasury_valid

        # [30] Real Yield Proxy
        # Approximate real yield = nominal yield - inflation proxy
        # Use VIX as inflation/uncertainty proxy (crude but useful)
        real_yield_raw, real_yield_valid = self._get_safe_float_with_validity(row, "real_yield_proxy", 0.0)
        if real_yield_valid:
            norm_cols_values[30] = float(np.tanh(real_yield_raw / 2.0))
        else:
            norm_cols_values[30] = 0.0
        norm_cols_validity[30] = real_yield_valid

        # [31] Days until earnings (normalized 0-1, 90 days = 1)
        days_until_raw, days_until_valid = self._get_safe_float_with_validity(
            row, "days_until_earnings", 90.0, min_value=0.0, max_value=365.0
        )
        if days_until_valid:
            # Normalize to 0-1 range (0 = today, 1 = 90+ days)
            norm_cols_values[31] = min(float(days_until_raw) / 90.0, 1.0)
        else:
            norm_cols_values[31] = 1.0  # Default: far from earnings
        norm_cols_validity[31] = days_until_valid

        # [32] Trailing dividend yield (normalized)
        div_yield_raw, div_yield_valid = self._get_safe_float_with_validity(
            row, "trailing_dividend_yield", 0.0, min_value=0.0, max_value=20.0
        )
        if div_yield_valid:
            # Normalize: typical yield 0-5%, use tanh(yield/3)
            norm_cols_values[32] = float(np.tanh(div_yield_raw / 3.0))
        else:
            norm_cols_values[32] = 0.0
        norm_cols_validity[32] = div_yield_valid

        # [33] Last earnings surprise (normalized via tanh)
        surprise_raw, surprise_valid = self._get_safe_float_with_validity(
            row, "last_earnings_surprise", 0.0, min_value=-100.0, max_value=100.0
        )
        if surprise_valid:
            # Normalize: typical surprise -20% to +20%, use tanh(surprise/15)
            norm_cols_values[33] = float(np.tanh(surprise_raw / 15.0))
        else:
            norm_cols_values[33] = 0.0
        norm_cols_validity[33] = surprise_valid

        # [34] In earnings blackout (binary flag)
        blackout_raw, blackout_valid = self._get_safe_float_with_validity(
            row, "in_earnings_blackout", 0.0, min_value=0.0, max_value=1.0
        )
        norm_cols_values[34] = float(blackout_raw) if blackout_valid else 0.0
        norm_cols_validity[34] = blackout_valid

        # NOTE: Normalization (tanh, clip) is applied in obs_builder.pyx when available.
        # In legacy fallback mode (when obs_builder is not available), normalization
        # is applied in the fallback path to ensure consistent behavior.
        return norm_cols_values, norm_cols_validity

    def _build_observation(self, *, row: Any | None, state: Any, mark_price: float) -> np.ndarray:
        """Build observation vector using obs_builder infrastructure with technical indicators."""
        obs_shape = getattr(getattr(self.env, "observation_space", None), "shape", None)
        if not obs_shape:
            return np.zeros(0, dtype=np.float32)

        # If obs_builder is not available, fall back to legacy implementation
        if not _HAVE_OBS_BUILDER:
            return self._build_observation_legacy(row=row, state=state, mark_price=mark_price)

        # Initialize observation array
        obs = np.zeros(obs_shape, dtype=np.float32)

        # Get environment and dataframe
        env = self.env
        df = getattr(env, "df", None)

        # Determine row index
        row_idx: int | None = getattr(self, "_context_row_idx", None)
        if row_idx is None and row is not None:
            try:
                row_idx = int(getattr(row, "name"))
            except Exception:
                row_idx = None
        if row_idx is None:
            try:
                step_idx = getattr(state, "step_idx", None)
                if step_idx is not None:
                    row_idx = int(step_idx)
            except Exception:
                row_idx = 0

        if row_idx is not None:
            if row_idx < 0:
                row_idx = 0
            if df is not None and row_idx >= len(df):
                row_idx = len(df) - 1

        # Calculate previous price and current price
        resolve_reward_price = getattr(env, "_resolve_reward_price", None)
        prev_price_val = self._coerce_finite(getattr(env, "_last_reward_price", 0.0), default=0.0)
        curr_price = mark_price

        if callable(resolve_reward_price):
            try:
                curr_price = float(resolve_reward_price(row_idx, row))
            except Exception:
                pass

        if not math.isfinite(curr_price) or curr_price <= 0.0:
            curr_price = mark_price if mark_price > 0.0 else 1.0

        # FIX (2025-11-26): Removed dead `prev_price_val is None` check
        # ═══════════════════════════════════════════════════════════════════════════
        # _coerce_finite() ALWAYS returns a float (default=0.0), never None.
        # The `is None` check was unreachable dead code.
        # Reference: _coerce_finite() at line 904-915
        # ═══════════════════════════════════════════════════════════════════════════
        if prev_price_val <= 0.0 and callable(resolve_reward_price):
            prev_idx = max(row_idx - 1, 0) if row_idx is not None else 0
            prev_row = None
            if df is not None and prev_idx < len(df):
                try:
                    prev_row = df.iloc[prev_idx]
                except Exception:
                    pass
            try:
                prev_price_candidate = float(resolve_reward_price(prev_idx, prev_row))
                if math.isfinite(prev_price_candidate) and prev_price_candidate > 0.0:
                    prev_price_val = float(prev_price_candidate)
            except Exception:
                pass

        if prev_price_val <= 0.0:
            prev_price_val = curr_price

        # Extract market data
        market_data = self._extract_market_data(row, state, curr_price, prev_price_val)

        # Extract technical indicators
        sim = getattr(env, "sim", None)
        indicators = self._extract_technical_indicators(row, sim, row_idx or 0)

        # Extract normalized columns WITH validity tracking (Issue #2 FIX - Phase 2 COMPLETE)
        norm_cols_values, norm_cols_validity = self._extract_norm_cols(row)
        # Convert validity to uint8 array for Cython (unsigned char[::1] in obs_builder.pyx)
        norm_cols_validity_uint8 = norm_cols_validity.astype(np.uint8)

        # Get state values
        units = self._coerce_finite(getattr(state, "units", 0.0), default=0.0)
        cash = self._coerce_finite(getattr(state, "cash", 0.0), default=0.0)

        # Get microstructure metrics from state if available
        last_vol_imbalance = self._coerce_finite(getattr(state, "last_vol_imbalance", 0.0), default=0.0)
        last_trade_intensity = self._coerce_finite(getattr(state, "last_trade_intensity", 0.0), default=0.0)
        last_realized_spread = self._coerce_finite(getattr(state, "last_realized_spread", 0.0), default=0.0)
        last_agent_fill_ratio = self._coerce_finite(getattr(state, "last_agent_fill_ratio", 0.0), default=0.0)

        # Fear & Greed
        # FIX (2025-11-26): Use _get_safe_float_with_validity to properly detect missing data.
        # PREVIOUS BUG: abs(value - 50.0) > 0.1 gave false negative when FG=50 (neutral).
        # FG=50 is a valid value meaning "neutral sentiment", NOT missing data!
        fear_greed_value, has_fear_greed = self._get_safe_float_with_validity(
            row, "fear_greed_value", default=50.0, min_value=0.0, max_value=100.0
        )

        # Event metadata
        is_high_importance = self._get_safe_float(row, "is_high_importance", 0.0)
        time_since_event = self._get_safe_float(row, "time_since_event", 0.0)

        # Risk-off flag (simplified: based on fear & greed)
        # Only set risk-off if we have valid FG data AND it indicates extreme fear
        risk_off_flag = has_fear_greed and fear_greed_value < 25.0

        # Token metadata (single token by default)
        token_id = getattr(state, "token_index", 0)
        max_num_tokens = 1
        num_tokens = 1

        # FIX (2025-11-24): Get signal_pos for observation vector
        # CRITICAL: In signal_only mode, model needs to know its target position
        signal_source = getattr(
            self,
            "_last_signal_position",
            getattr(self.env, "_last_signal_position", 0.0),
        )
        signal_pos = self._coerce_finite(signal_source, default=0.0)

        # Call obs_builder to construct observation vector
        # Phase 2 of ISSUE #2 fix: Now passing validity flags to enable model
        # to distinguish missing data (NaN) from zero values
        try:
            build_observation_vector(
                float(market_data["price"]),
                float(market_data["prev_price"]),
                float(market_data["log_volume_norm"]),
                float(market_data["rel_volume"]),
                float(indicators["ma5"]),
                float(indicators["ma20"]),
                float(indicators["rsi14"]),
                float(indicators["macd"]),
                float(indicators["macd_signal"]),
                float(indicators["momentum"]),
                float(indicators["atr"]),
                float(indicators["cci"]),
                float(indicators["obv"]),
                float(indicators["bb_lower"]),
                float(indicators["bb_upper"]),
                float(is_high_importance),
                float(time_since_event),
                float(fear_greed_value),
                bool(has_fear_greed),
                bool(risk_off_flag),
                float(cash),
                float(units),
                float(signal_pos),
                float(last_vol_imbalance),
                float(last_trade_intensity),
                float(last_realized_spread),
                float(last_agent_fill_ratio),
                int(token_id),
                int(max_num_tokens),
                int(num_tokens),
                norm_cols_values,
                norm_cols_validity_uint8,
                True,  # enable_validity_flags=True (hardcoded for Phase 2)
                obs,
            )
        except Exception as e:
            # If obs_builder fails, fall back to legacy
            import logging
            logging.getLogger(__name__).warning(f"obs_builder failed: {e}, falling back to legacy")
            return self._build_observation_legacy(row=row, state=state, mark_price=mark_price)

        return obs

    def _build_observation_legacy(self, *, row: Any | None, state: Any, mark_price: float) -> np.ndarray:
        """Legacy observation builder (fallback when obs_builder is not available)."""
        obs_shape = getattr(getattr(self.env, "observation_space", None), "shape", None)
        if not obs_shape:
            return np.zeros(0, dtype=np.float32)
        obs = np.zeros(obs_shape, dtype=np.float32)
        # Try to populate front slots with common market columns when available
        if row is not None:
            try:
                columns = getattr(row, "index", [])
            except Exception:
                columns = []
            col_order = [
                "open",
                "high",
                "low",
                "close",
                "price",
                "bid",
                "ask",
                "quote_asset_volume",
            ]
            pos = 0
            tail_slots = 4
            tail_reserve = tail_slots if obs.shape[0] >= tail_slots else min(obs.shape[0], tail_slots)
            for name in col_order:
                if pos >= max(0, obs.shape[0] - tail_reserve):
                    break
                try:
                    if columns is not None and name not in columns:
                        continue
                except Exception:
                    # fallback to getattr
                    pass
                try:
                    val = row.get(name) if hasattr(row, "get") else getattr(row, name, None)
                except Exception:
                    val = None
                if val is None:
                    continue
                coerced = self._coerce_finite(val, default=0.0)
                obs[pos] = coerced
                pos += 1
        # Always include mark price, units and cash in the tail slots if possible
        mark_value = self._coerce_finite(mark_price, default=0.0)
        if obs.size:
            obs[0] = mark_value
        units = self._coerce_finite(getattr(state, "units", 0.0), default=0.0)
        cash = self._coerce_finite(getattr(state, "cash", 0.0), default=0.0)
        signal_source = getattr(
            self,
            "_last_signal_position",
            getattr(self.env, "_last_signal_position", 0.0),
        )
        signal_pos = self._coerce_finite(signal_source, default=0.0)
        log_ret_prev = 0.0
        env = self.env
        df = getattr(env, "df", None)
        row_idx: int | None = getattr(self, "_context_row_idx", None)
        if row_idx is None and row is not None:
            try:
                row_idx = int(getattr(row, "name"))
            except Exception:
                row_idx = None
        if row_idx is None:
            try:
                step_idx = getattr(state, "step_idx", None)
                if step_idx is not None:
                    row_idx = int(step_idx)
            except Exception:
                row_idx = None
        if row_idx is not None:
            if row_idx < 0:
                row_idx = 0
            if df is not None and row_idx >= len(df):
                row_idx = len(df) - 1
            resolve_reward_price = getattr(env, "_resolve_reward_price", None)
            prev_price = self._coerce_finite(getattr(env, "_last_reward_price", 0.0), default=0.0)
            curr_price: float | None = None
            if callable(resolve_reward_price):
                try:
                    curr_price = float(resolve_reward_price(row_idx, row))
                except Exception:
                    curr_price = None
            if curr_price is None or not math.isfinite(curr_price) or curr_price <= 0.0:
                curr_price = mark_value if mark_value > 0.0 else None
            if (prev_price is None or prev_price <= 0.0) and callable(resolve_reward_price):
                prev_idx = max(row_idx - 1, 0)
                prev_row = None
                if df is not None and prev_idx < len(df):
                    try:
                        prev_row = df.iloc[prev_idx]
                    except Exception:
                        prev_row = None
                try:
                    prev_price_candidate = float(resolve_reward_price(prev_idx, prev_row))
                except Exception:
                    prev_price_candidate = None
                if prev_price_candidate is not None and math.isfinite(prev_price_candidate) and prev_price_candidate > 0.0:
                    prev_price = float(prev_price_candidate)
            if curr_price is not None and math.isfinite(curr_price) and curr_price > 0.0 and prev_price > 0.0:
                log_ret_prev = math.log(curr_price / prev_price)
                mark_value = float(curr_price)
                if obs.size:
                    obs[0] = float(mark_value)
        self._latest_log_ret_prev = float(log_ret_prev)

        tail_values = (units, cash, signal_pos, float(log_ret_prev))
        tail_count = min(len(tail_values), obs.size)
        for offset in range(1, tail_count + 1):
            obs[-offset] = float(tail_values[-offset])
        return obs

    def step(self, proto: ActionProto):
        env = self.env
        state = getattr(env, "state", None)
        if state is None:
            raise RuntimeError("Mediator requires environment state")

        current_idx = int(getattr(state, "step_idx", 0) or 0)
        df = getattr(env, "df", None)
        row_idx = self._context_row_idx if self._context_row_idx is not None else current_idx
        row = self._context_row
        if row is None and df is not None:
            try:
                if 0 <= row_idx < len(df):
                    row = df.iloc[row_idx]
            except Exception:
                row = None

        timestamp = self._context_timestamp
        if timestamp is None:
            if row is not None and hasattr(env, "_resolve_snapshot_timestamp"):
                try:
                    timestamp = int(env._resolve_snapshot_timestamp(row))
                except Exception:
                    timestamp = None
        if timestamp is None:
            timestamp = int(now_ms())

        report = self.step_action(proto, timestamp=timestamp)

        trades = list(report.get("trades", []))
        cancelled_ids = [int(x) for x in report.get("cancelled_ids", [])]
        new_order_ids = [int(x) for x in report.get("new_order_ids", [])]
        fee_total = float(report.get("fee_total", 0.0) or 0.0)
        events = list(report.get("events", []))

        executed_notional = 0.0
        for price, volume, _is_buy, _maker_is_agent in trades:
            try:
                executed_notional += abs(float(price) * float(volume))
            except Exception:
                continue

        # Update agent order tracker if env.state holds it
        agent_orders = getattr(state, "agent_orders", None)
        if agent_orders is not None:
            try:
                for cid in cancelled_ids:
                    agent_orders.discard(int(cid))
                for oid in new_order_ids:
                    agent_orders.add(int(oid))
            except Exception:
                pass

        # Reduce pending expected volume counters
        for _price, vol, is_buy, _maker_is_agent in trades:
            try:
                vol_f = float(vol)
            except Exception:
                continue
            if is_buy:
                self._pending_buy_volume = max(0.0, float(self._pending_buy_volume) - vol_f)
            else:
                self._pending_sell_volume = max(0.0, float(self._pending_sell_volume) - vol_f)

        mark_price = getattr(env, "last_mtm_price", None)
        if mark_price is None:
            mark_price = getattr(env, "last_mid", None)
        if mark_price is None and row is not None:
            for key in ("close", "price", "open"):
                if hasattr(row, "get"):
                    candidate = row.get(key)
                else:
                    candidate = getattr(row, key, None)
                if candidate is not None:
                    try:
                        mark_price = float(candidate)
                        break
                    except Exception:
                        continue
        mark_price = self._coerce_finite(mark_price, default=0.0)

        cash = self._coerce_finite(getattr(state, "cash", 0.0), default=0.0)
        units = self._coerce_finite(getattr(state, "units", 0.0), default=0.0)
        net_worth = cash + units * mark_price
        try:
            state.net_worth = float(net_worth)
        except Exception:
            pass
        peak_value = float(getattr(state, "peak_value", net_worth) or net_worth)
        if net_worth > peak_value:
            try:
                state.peak_value = float(net_worth)
            except Exception:
                pass

        max_steps = int(getattr(env, "_max_steps", 0) or 0)
        next_idx = current_idx + 1
        truncated = False
        if max_steps > 0 and next_idx >= max_steps:
            truncated = True
            next_idx = max_steps
        try:
            state.step_idx = int(next_idx)
        except Exception:
            pass

        bankruptcy_th = float(getattr(env, "bankruptcy_cash_th", -1e12) or -1e12)
        is_bankrupt = bool(getattr(state, "is_bankrupt", False))
        if not is_bankrupt and cash <= bankruptcy_th:
            is_bankrupt = True
            try:
                state.is_bankrupt = True
            except Exception:
                pass

        info = dict(report.get("info", {}))
        info.setdefault("executed_notional", executed_notional)
        info.setdefault("turnover", executed_notional)
        info.setdefault("fee_total", fee_total)
        info.setdefault("mark_price", mark_price)
        info.setdefault("cash", cash)
        info.setdefault("units", units)
        info.setdefault("net_worth", net_worth)
        info.setdefault("step_idx", current_idx)
        info.setdefault(
            "signal_pos",
            self._coerce_finite(
                getattr(self, "_last_signal_position", getattr(env, "_last_signal_position", 0.0)),
                default=0.0,
            ),
        )
        info["trades"] = trades
        info["cancelled_ids"] = cancelled_ids
        info["new_order_ids"] = new_order_ids
        info["events"] = events

        # FIX (2025-11-25): Build observation from NEXT row (Gymnasium semantics)
        # ═══════════════════════════════════════════════════════════════════════
        # PROBLEM: step() returned observation from SAME row as action was based on.
        # FIX: Use next_idx for observation, capped at len(df)-1 for terminal states.
        # SEMANTICS: step(a) → (s_{t+1}, r_t, ...) where s_{t+1} is NEXT state
        # See trading_patchnew.py:1007-1037 for full documentation.
        # Tests: tests/test_step_observation_next_row.py (6 tests)
        # ═══════════════════════════════════════════════════════════════════════
        obs_row_idx = min(next_idx, len(df) - 1) if df is not None and len(df) > 0 else 0
        next_row = df.iloc[obs_row_idx] if df is not None and len(df) > obs_row_idx else row
        next_mark_price = mark_price
        resolve_reward_price = getattr(env, "_resolve_reward_price", None)
        if callable(resolve_reward_price):
            try:
                candidate = float(resolve_reward_price(obs_row_idx, next_row))
                if math.isfinite(candidate) and candidate > 0.0:
                    next_mark_price = candidate
            except Exception:
                pass
        obs = self._build_observation(row=next_row, state=state, mark_price=next_mark_price)

        info.setdefault(
            "log_ret_prev",
            self._coerce_finite(getattr(self, "_latest_log_ret_prev", 0.0), default=0.0),
        )

        terminated = is_bankrupt
        if info.get("risk_event") in {"BANKRUPT", "STOP_TRADE"}:
            terminated = True

        self._context_row = None
        self._context_row_idx = None
        self._context_timestamp = None

        reward = 0.0
        return obs, float(reward), bool(terminated), bool(truncated), info

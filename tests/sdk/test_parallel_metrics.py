"""Before/after tests for parallel metric execution (Fix #2).

Compare the old sequential path with the gather-based path. Concurrency is
asserted directly; wall-clock measurements remain diagnostic benchmarks.
"""

import asyncio
import logging
import time

import pytest
from unittest.mock import MagicMock, AsyncMock, patch

from qym.core.evaluator import Evaluator


# ---------------------------------------------------------------------------
# Helpers
# ---------------------------------------------------------------------------

def _make_evaluator(metrics_dict, max_metric_concurrency=5):
    """Create a minimal Evaluator wired for _evaluate_item testing."""
    with patch("qym.core.evaluator.auto_detect_task"):
        evaluator = Evaluator(
            task=MagicMock(),
            dataset=MagicMock(),
            metrics=[],
            config={
                "run_name": "bench",
                "max_metric_concurrency": max_metric_concurrency,
            },
            langfuse_client=None,
        )
    evaluator.task_adapter = MagicMock()
    evaluator.task_adapter.arun = AsyncMock(return_value="output")
    evaluator._notify_observer = MagicMock()
    evaluator.model_name = "test"
    evaluator.metrics = metrics_dict
    return evaluator


def _make_item(input_val="hello", expected="world"):
    item = MagicMock()
    item.input = input_val
    item.expected_output = expected
    item.id = "item_0"
    item.metadata = {}
    return item


async def _run_metrics_sequentially(evaluator, output, expected_output, item_input):
    """Simulate the OLD sequential metric loop for comparison."""
    scores = {}
    for m_name, m_func in evaluator.metrics.items():
        if asyncio.iscoroutinefunction(m_func):
            score = await evaluator._compute_metric(
                m_func, output, expected_output, item_input,
            )
        else:
            score = await asyncio.to_thread(
                evaluator._compute_metric_sync,
                m_func, output, expected_output, item_input,
            )
        scores[m_name] = score
    return scores


# ---------------------------------------------------------------------------
# Tests
# ---------------------------------------------------------------------------

class TestParallelMetrics:

    @pytest.mark.asyncio
    async def test_three_async_metrics_sequential_vs_parallel(self, record_property):
        """All three metrics must start before any may finish."""

        parallel_phase = False
        started = 0
        all_started = asyncio.Event()

        async def slow_metric(output, expected):
            nonlocal started
            if parallel_phase:
                started += 1
                if started == 3:
                    all_started.set()
                await all_started.wait()
            await asyncio.sleep(0.5)
            return 1.0

        metrics = {"m1": slow_metric, "m2": slow_metric, "m3": slow_metric}
        evaluator = _make_evaluator(metrics)
        item = _make_item()
        tracker = MagicMock()

        # OLD path — sequential
        t0 = time.monotonic()
        seq_scores = await _run_metrics_sequentially(
            evaluator, "output", "world", "hello",
        )
        sequential_time = time.monotonic() - t0

        # NEW path — parallel via _evaluate_item's gather
        parallel_phase = True
        t0 = time.monotonic()
        # A serial implementation cannot release the barrier. The timeout is
        # only a deadlock guard, independent of the benchmark's speed ratio.
        result = await asyncio.wait_for(evaluator._evaluate_item(0, item, tracker), 10)
        parallel_time = time.monotonic() - t0
        assert started == 3 and all_started.is_set()

        # Correctness: both paths produce the same scores
        assert set(seq_scores.keys()) == set(result["scores"].keys())
        for k in seq_scores:
            assert seq_scores[k] == result["scores"][k]

        # Runner load and task setup can dominate a short wall-clock sample.
        # Keep the benchmark in test reports, but gate on actual concurrency.
        speedup = sequential_time / parallel_time
        record_property("sequential_seconds", sequential_time)
        record_property("parallel_seconds", parallel_time)
        record_property("speedup", speedup)

    @pytest.mark.asyncio
    async def test_mixed_async_sync_metrics_produce_same_scores(self):
        """Async + sync metrics under gather must return identical scores to sequential."""

        async def async_metric(output, expected):
            await asyncio.sleep(0.5)
            return {"score": 1.0, "metadata": {"kind": "async"}}

        def sync_metric(output, expected):
            time.sleep(0.5)
            return {"score": 0.5, "metadata": {"kind": "sync"}}

        metrics = {"async_m": async_metric, "sync_m": sync_metric}
        evaluator = _make_evaluator(metrics)
        item = _make_item()
        tracker = MagicMock()

        # OLD path — sequential
        seq_scores = await _run_metrics_sequentially(
            evaluator, "output", "world", "hello",
        )

        # NEW path — parallel
        result = await evaluator._evaluate_item(0, item, tracker)

        # Pure correctness — no timing assertions
        assert seq_scores["async_m"] == result["scores"]["async_m"]
        assert seq_scores["sync_m"] == result["scores"]["sync_m"]

    @pytest.mark.asyncio
    async def test_metric_error_isolated_under_gather(self):
        """A failing metric must not cancel or corrupt sibling metrics."""

        async def good_metric(output, expected):
            await asyncio.sleep(0.2)
            return 1.0

        async def bad_metric(output, expected):
            await asyncio.sleep(0.1)
            raise ValueError("boom")

        evaluator = _make_evaluator({"good": good_metric, "bad": bad_metric})
        item = _make_item()
        tracker = MagicMock()

        result = await evaluator._evaluate_item(0, item, tracker)

        assert result["success"] is True
        assert result["scores"]["good"] == 1.0
        assert result["scores"]["bad"]["score"] == 0
        assert "boom" in result["scores"]["bad"]["error"]

    @pytest.mark.asyncio
    async def test_single_metric_regression(self):
        """One metric should still work after the gather refactor."""

        async def only_metric(output, expected):
            await asyncio.sleep(0.1)
            return 0.75

        evaluator = _make_evaluator({"only": only_metric})
        item = _make_item()
        tracker = MagicMock()

        result = await evaluator._evaluate_item(0, item, tracker)
        assert result["success"] is True
        assert result["scores"]["only"] == 0.75

    @pytest.mark.asyncio
    async def test_semaphore_bounds_concurrent_metrics(self):
        """With max_metric_concurrency=2, only 2 metrics run at a time.

        6 metrics × 0.3s each, capped at 2 concurrent → ~0.9s (3 batches).
        Uncapped would be ~0.3s; sequential would be ~1.8s.
        We verify the parallel time sits between the two extremes.
        """

        peak_concurrent = 0
        current_concurrent = 0
        lock = asyncio.Lock()

        async def counting_metric(output, expected):
            nonlocal peak_concurrent, current_concurrent
            async with lock:
                current_concurrent += 1
                peak_concurrent = max(peak_concurrent, current_concurrent)
            try:
                await asyncio.sleep(0.3)
                return 1.0
            finally:
                async with lock:
                    current_concurrent -= 1

        metrics = {f"m{i}": counting_metric for i in range(6)}
        evaluator = _make_evaluator(metrics, max_metric_concurrency=2)
        item = _make_item()
        tracker = MagicMock()

        result = await evaluator._evaluate_item(0, item, tracker)

        assert result["success"] is True
        assert len(result["scores"]) == 6
        assert peak_concurrent == 2, (
            f"Peak concurrency was {peak_concurrent} — expected two concurrent metrics"
        )


# ---------------------------------------------------------------------------
# Metric blocking detection tests
# ---------------------------------------------------------------------------

class TestMetricBlockingDetection:
    """Verify that async metrics with blocking I/O are detected and warned."""

    def setup_method(self):
        """Reset probed/warned sets before each test."""
        Evaluator._metric_blocking_probed = set()
        Evaluator._metric_blocking_warned = set()

    @pytest.mark.asyncio
    async def test_blocking_async_metric_detected(self, caplog):
        """An async metric with time.sleep must trigger a warning."""

        async def blocking_metric(output, expected):
            time.sleep(1.5)
            return 1.0

        evaluator = _make_evaluator({"blocker": blocking_metric})
        item = _make_item()
        tracker = MagicMock()

        with caplog.at_level(logging.WARNING, logger="qym.core.evaluator"):
            result = await evaluator._evaluate_item(0, item, tracker)

        assert result["success"] is True
        assert result["scores"]["blocker"] == 1.0
        warnings = [r for r in caplog.records if "block the event loop" in r.message]
        assert len(warnings) == 1, (
            f"Expected exactly 1 blocking warning, got {len(warnings)}"
        )

    @pytest.mark.asyncio
    async def test_wellbehaved_async_metric_not_flagged(self, caplog):
        """A proper async metric must NOT trigger a warning."""

        async def good_metric(output, expected):
            await asyncio.sleep(1.5)
            return 0.9

        evaluator = _make_evaluator({"good": good_metric})
        item = _make_item()
        tracker = MagicMock()

        with caplog.at_level(logging.WARNING, logger="qym.core.evaluator"):
            result = await evaluator._evaluate_item(0, item, tracker)

        assert result["scores"]["good"] == 0.9
        warnings = [r for r in caplog.records if "block the event loop" in r.message]
        assert len(warnings) == 0

    @pytest.mark.asyncio
    async def test_sync_metric_not_probed(self, caplog):
        """Sync metrics run in thread pool — no detection needed."""

        def sync_metric(output, expected):
            time.sleep(0.5)
            return 0.8

        evaluator = _make_evaluator({"sync_m": sync_metric})
        item = _make_item()
        tracker = MagicMock()

        with caplog.at_level(logging.WARNING, logger="qym.core.evaluator"):
            result = await evaluator._evaluate_item(0, item, tracker)

        assert result["scores"]["sync_m"] == 0.8
        warnings = [r for r in caplog.records if "block the event loop" in r.message]
        assert len(warnings) == 0

    @pytest.mark.asyncio
    async def test_metric_warning_emitted_once_across_items(self, caplog):
        """Repeated evaluations of the same blocking metric produce one warning."""

        async def blocking_metric(output, expected):
            time.sleep(1.5)
            return 1.0

        evaluator = _make_evaluator({"blocker": blocking_metric})
        tracker = MagicMock()

        with caplog.at_level(logging.WARNING, logger="qym.core.evaluator"):
            await evaluator._evaluate_item(0, _make_item(), tracker)
            await evaluator._evaluate_item(1, _make_item(), tracker)

        warnings = [r for r in caplog.records if "block the event loop" in r.message]
        assert len(warnings) == 1, (
            f"Expected exactly 1 warning across 2 items, got {len(warnings)}"
        )

    @pytest.mark.asyncio
    async def test_probe_only_runs_once_per_function(self):
        """After the first probe, subsequent calls skip the heartbeat overhead."""

        async def fast_metric(output, expected):
            return 1.0

        func_id = id(fast_metric)
        evaluator = _make_evaluator({"fast": fast_metric})
        tracker = MagicMock()

        # First call — probes
        await evaluator._evaluate_item(0, _make_item(), tracker)
        assert func_id in Evaluator._metric_blocking_probed

        # Second call — should skip probe (already in probed set)
        await evaluator._evaluate_item(1, _make_item(), tracker)
        # If it probed again, this would be a no-op since set already has it,
        # but the point is verified by the code path (no heartbeat overhead).
        assert func_id in Evaluator._metric_blocking_probed

    @pytest.mark.asyncio
    async def test_blocking_metric_detected_even_when_raises(self, caplog):
        """A blocking metric that also raises must still trigger the warning."""

        async def blocking_then_raise(output, expected):
            time.sleep(1.5)
            raise ValueError("metric failed")

        evaluator = _make_evaluator({"bad": blocking_then_raise})
        item = _make_item()
        tracker = MagicMock()

        with caplog.at_level(logging.WARNING, logger="qym.core.evaluator"):
            result = await evaluator._evaluate_item(0, item, tracker)

        # Metric error is caught and returned as error dict
        assert "metric failed" in result["scores"]["bad"]["error"]
        warnings = [r for r in caplog.records if "block the event loop" in r.message]
        assert len(warnings) == 1, (
            "Detection must fire even when the metric raises — "
            f"got {len(warnings)} warnings"
        )

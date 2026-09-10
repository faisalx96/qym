import pytest
from unittest.mock import MagicMock, patch, AsyncMock
import asyncio
from qym.core.dashboard import RunDashboard
from qym.core.evaluator import (
    Evaluator,
    ItemSpans,
    TaskAttemptResult,
    _graceful_interrupt_signals,
)
from qym.core.dataset import CsvDataset
from qym import BusinessRuleError
import signal


class TestEvaluator:
    @pytest.mark.asyncio
    @pytest.mark.parametrize("is_async", [False, True], ids=["sync", "async"])
    async def test_business_rule_task_stops_retries_and_skips_metrics(
        self, mock_dataset, is_async
    ):
        attempts = []
        metric_calls = []

        def reject(question):
            attempts.append(question)
            raise BusinessRuleError()

        async def async_reject(question):
            return reject(question)

        def metric(output, expected):
            metric_calls.append(output)
            return 1.0

        evaluator = Evaluator(
            task=async_reject if is_async else reject,
            dataset=mock_dataset,
            metrics=[metric],
            config={"run_name": "business-error", "max_retries": 3},
        )
        evaluator._create_item_spans = MagicMock(return_value=ItemSpans())
        evaluator._platform_stream = MagicMock()
        item = MagicMock(id="item-1", input="question", expected_output="answer")
        item.metadata = {}

        result = await evaluator._evaluate_item(0, item, MagicMock())

        assert attempts == ["question"]
        assert metric_calls == []
        assert "BusinessRuleError" in result["_error"]
        failures = [
            payload
            for event_type, payload in (
                call.args for call in evaluator._platform_stream.emit.call_args_list
            )
            if event_type == "item_failed"
        ]
        assert len(failures) == 1
        assert failures[0]["retry_count"] == 0

    @pytest.mark.asyncio
    @pytest.mark.parametrize("is_async", [False, True], ids=["sync", "async"])
    @pytest.mark.parametrize("error_type", [BusinessRuleError, RuntimeError])
    @pytest.mark.parametrize("message", ["", "  "])
    async def test_metric_exceptions_with_blank_messages_keep_error_status(
        self, mock_task, mock_dataset, is_async, error_type, message
    ):
        calls = []

        def fail(output, expected):
            calls.append(1)
            raise error_type(message)

        async def async_fail(output, expected):
            return fail(output, expected)

        class Stream:
            def __init__(self):
                self.events = []

            async def aemit(self, event_type, payload, *, sync=False):
                self.events.append((event_type, payload))

            def emit(self, *args, **kwargs):
                raise AssertionError("Use asynchronous platform emission")

        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,
                metrics=[],
                config={"run_name": "metric-errors", "metric_max_retries": 3},
            )
        evaluator.metrics = {
            "broken": async_fail if is_async else fail,
            "healthy": lambda output, expected: 1.0,
        }
        evaluator.task_adapter.arun = AsyncMock(return_value="answer")
        evaluator._create_item_spans = MagicMock(return_value=ItemSpans())
        evaluator._notify_observer = MagicMock()
        stream = evaluator._platform_stream = Stream()
        tracker = MagicMock()
        item = MagicMock(id="item-1", input="question", expected_output="answer")
        item.metadata = {}

        result = await evaluator._evaluate_item(0, item, tracker)

        assert result["success"] is True
        assert len(calls) == 1
        scores = {
            payload["metric_name"]: payload
            for event_type, payload in stream.events
            if event_type == "metric_scored"
        }
        broken = scores["broken"]
        assert broken["score_numeric"] == 0
        assert broken["meta"]["status"] == "error"
        assert broken["meta"]["error"] == error_type.__name__
        assert error_type.__name__ in broken["meta"]["traceback"]
        assert scores["healthy"]["score_numeric"] == 1
        assert "error" not in scores["healthy"]["meta"]
        tracker.set_metric_error.assert_called_once_with(0, "broken")
        tracker.update_metric.assert_called_once_with(0, "healthy", 1.0, {})

    def test_graceful_interrupt_signals_translate_sigterm_to_keyboard_interrupt(self):
        previous = signal.getsignal(signal.SIGTERM)
        with _graceful_interrupt_signals():
            handler = signal.getsignal(signal.SIGTERM)
            assert callable(handler)
            with pytest.raises(KeyboardInterrupt):
                handler(signal.SIGTERM, None)
        assert signal.getsignal(signal.SIGTERM) == previous

    def test_init(self, mock_task, mock_dataset):
        """Test basic initialization of Evaluator with DI."""
        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,  # Injected dataset
                metrics=["exact_match"],
                config={"run_name": "test-run"},
            )

            assert evaluator.dataset == mock_dataset
            # Evaluator appends a timestamp suffix for uniqueness
            assert evaluator.run_name.startswith("test-run")
            assert "exact_match" in evaluator.metrics

    def test_init_ignores_deprecated_langfuse_client(
        self, mock_task, mock_langfuse, mock_dataset
    ):
        """langfuse_client is deprecated: accepted for compatibility but ignored."""
        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,
                metrics=[],
                config={"run_name": "test-run"},
                langfuse_client=mock_langfuse,
            )

        assert evaluator.client is None
        assert evaluator.langfuse_enabled is False

    @pytest.mark.asyncio
    async def test_evaluate_item_success(self, mock_task, mock_dataset):
        """Test _evaluate_item method success path."""
        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,
                metrics=[],
                config={"run_name": "test-run"},
            )

            # Mock internal components
            evaluator.task_adapter = MagicMock()
            evaluator.task_adapter.arun = AsyncMock(return_value="test_output")
            evaluator._notify_observer = MagicMock()
            evaluator.model_name = "test-model"

            # Mock item
            item = MagicMock()
            item.input = "test_input"

            tracker = MagicMock()

            result = await evaluator._evaluate_item(0, item, tracker)

            assert result["success"] is True
            assert result["output"] == "test_output"
            tracker.start_item.assert_called_once_with(0)
            tracker.complete_item.assert_called_once()
            complete_args, complete_kwargs = tracker.complete_item.call_args
            assert complete_args == (0,)
            assert complete_kwargs["elapsed_time"] >= 0

    @pytest.mark.asyncio
    @pytest.mark.parametrize("task_output", [None, ""])
    async def test_none_and_empty_task_outputs_are_normal_results(
        self, task_output, mock_task, mock_langfuse, mock_dataset
    ):
        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,
                metrics=[],
                config={"run_name": "empty-task-output"},
                langfuse_client=mock_langfuse,
            )

        evaluator.task_adapter = MagicMock()
        evaluator.task_adapter.arun = AsyncMock(return_value=task_output)
        evaluator.model_name_full = "test-model"
        evaluator._create_item_spans = MagicMock(return_value=ItemSpans())

        item = MagicMock()
        item.input = "question"
        item.id = "item-1"

        attempt = await evaluator._run_single_task_attempt(0, item, 1)

        assert attempt.success is True
        assert attempt.output == task_output

    @pytest.mark.asyncio
    async def test_task_output_envelope_passes_metadata_to_metric_and_platform(
        self, mock_task, mock_langfuse, mock_dataset
    ):
        captured = {}

        def context_metric(output, expected):
            captured["output"] = output
            return {
                "score": 1.0
                if output["metadata"]["retrieved_context"][0] == "doc-1"
                else 0.0,
                "metadata": {
                    "context_count": len(output["metadata"]["retrieved_context"])
                },
            }

        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,
                metrics=[context_metric],
                config={"run_name": "task-envelope"},
                langfuse_client=mock_langfuse,
            )

        evaluator.task_adapter = MagicMock()
        evaluator.task_adapter.arun = AsyncMock(
            return_value={
                "output": "answer",
                "metadata": {"retrieved_context": ["doc-1"]},
            }
        )
        evaluator._notify_observer = MagicMock()
        evaluator._platform_stream = MagicMock()
        evaluator.model_name = "test-model"

        item = MagicMock()
        item.input = "question"
        item.expected_output = "answer"
        item.metadata = {"category": "rag"}
        item.id = "item-1"

        tracker = MagicMock()
        result = await evaluator._evaluate_item(0, item, tracker)

        assert result["success"] is True
        assert result["output"] == "answer"
        assert result["task_metadata"] == {"retrieved_context": ["doc-1"]}
        assert result["item_metadata"] == {
            "category": "rag",
            "task_metadata": {"retrieved_context": ["doc-1"]},
        }
        assert captured == {
            "output": {
                "output": "answer",
                "metadata": {"retrieved_context": ["doc-1"]},
            },
        }

        emitted = [call.args for call in evaluator._platform_stream.emit.call_args_list]
        completed = [
            payload for event_type, payload in emitted if event_type == "item_completed"
        ]
        assert completed[0]["output"] == "answer"
        assert completed[0]["item_metadata"]["task_metadata"] == {
            "retrieved_context": ["doc-1"]
        }

    @pytest.mark.asyncio
    async def test_dict_task_output_must_use_output_metadata_envelope(
        self, mock_task, mock_langfuse, mock_dataset
    ):
        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,
                metrics=[],
                config={"run_name": "bad-task-envelope", "max_retries": 0},
                langfuse_client=mock_langfuse,
            )

        evaluator.task_adapter = MagicMock()
        evaluator.task_adapter.arun = AsyncMock(return_value={"answer": "Paris"})
        evaluator._notify_observer = MagicMock()
        evaluator._platform_stream = MagicMock()
        evaluator.model_name = "test-model"

        item = MagicMock()
        item.input = "question"
        item.expected_output = "Paris"
        item.metadata = {}
        item.id = "item-1"

        tracker = MagicMock()
        result = await evaluator._evaluate_item(0, item, tracker)

        assert "_error" in result
        assert "Dict task outputs must use qym's envelope" in result["_error"]

    @pytest.mark.asyncio
    async def test_csv_dataset_without_langfuse_credentials_does_not_require_client(
        self, tmp_path, mock_task, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,world\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        # Ensure a deterministic no-credentials environment even if the developer machine has Langfuse env vars.
        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=ds,
                metrics=[],
                config={"run_name": "csv-run"},
                langfuse_client=None,
            )

        assert evaluator.client is None

        evaluator.task_adapter = MagicMock()
        evaluator.task_adapter.arun = AsyncMock(return_value="ok")
        evaluator._notify_observer = MagicMock()
        evaluator.model_name = "test-model"

        item = ds.get_items()[0]
        tracker = MagicMock()
        res = await evaluator._evaluate_item(0, item, tracker)
        assert res["success"] is True
        assert res["output"] == "ok"

    @pytest.mark.asyncio
    async def test_run_sends_none_and_empty_output_to_metrics(
        self, tmp_path, monkeypatch
    ):
        dataset_path = tmp_path / "empty-output.csv"
        dataset_path.write_text(
            "question,expected\nreturn-none,answer\nreturn-empty,answer\n",
            encoding="utf-8",
        )
        dataset = CsvDataset(
            dataset_path,
            input_col="question",
            expected_col="expected",
        )
        task_attempts = {"return-none": 0, "return-empty": 0}
        metric_outputs = []

        def empty_task(question):
            task_attempts[question] += 1
            return None if question == "return-none" else ""

        def zero_metric(output, expected):
            del expected
            metric_outputs.append(output)
            return 0.0

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)
        monkeypatch.delenv("QYM_API_KEY", raising=False)
        evaluator = Evaluator(
            task=empty_task,
            dataset=dataset,
            metrics=[zero_metric],
            config={
                "run_name": "empty-output-normal-result",
                "max_retries": 1,
                "max_concurrency": 1,
                "checkpoint_enabled": False,
                "otel_enabled": False,
            },
        )

        result = await evaluator.arun(show_tui=False, auto_save=False)

        assert task_attempts == {"return-none": 1, "return-empty": 1}
        assert metric_outputs == [None, ""]
        assert len(result.results) == 2
        assert result.errors == {}

    @pytest.mark.asyncio
    async def test_run_single_task_attempt_emits_item_attempt_started(
        self, mock_task, mock_langfuse, mock_dataset
    ):
        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,
                metrics=[],
                config={"run_name": "attempt-start"},
                langfuse_client=mock_langfuse,
            )

        evaluator.task_adapter = MagicMock()
        evaluator.task_adapter.arun = AsyncMock(return_value="ok")
        evaluator.model_name_full = "test-model"
        evaluator._current_pass = 3
        evaluator._platform_stream = MagicMock()
        evaluator._create_item_spans = MagicMock(
            return_value=ItemSpans(trace_id="trace-1", trace_url="url-1")
        )

        item = MagicMock()
        item.input = "test_input"
        item.id = "item-1"

        result = await evaluator._run_single_task_attempt(0, item, 1)

        assert result.success is True
        assert result.spans.trace_id == "trace-1"
        emitted = [call.args for call in evaluator._platform_stream.emit.call_args_list]
        started = [
            payload
            for event_type, payload in emitted
            if event_type == "item_attempt_started"
        ]
        assert len(started) == 1
        assert started[0]["item_id"] == "item-1"
        assert started[0]["pass_number"] == 3
        assert started[0]["attempt_number"] == 1
        assert started[0]["trace_id"] == "trace-1"
        assert started[0]["trace_url"] == "url-1"
        assert started[0]["task_started_at_ms"] is not None

    @pytest.mark.asyncio
    async def test_run_single_task_attempt_does_not_mislabel_inner_timeout_as_qym_timeout(
        self, mock_task, mock_langfuse, mock_dataset
    ):
        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,
                metrics=[],
                config={"run_name": "attempt-inner-timeout", "timeout": 1800},
                langfuse_client=mock_langfuse,
            )

        evaluator.task_adapter = MagicMock()
        evaluator.task_adapter.arun = AsyncMock(
            side_effect=asyncio.TimeoutError("client timeout after 240s")
        )
        evaluator.model_name_full = "test-model"
        evaluator._create_item_spans = MagicMock(
            return_value=ItemSpans(trace_id="trace-1", trace_url="url-1")
        )

        item = MagicMock()
        item.input = "test_input"
        item.id = "item-1"

        result = await evaluator._run_single_task_attempt(0, item, 1)

        assert result.success is False
        assert "TaskExecutionTimeoutError" in result.error
        assert "client timeout after 240s" in result.error
        assert "Task timed out after 1800s" not in result.error

    @pytest.mark.asyncio
    async def test_evaluate_item_uses_last_attempt_trace_and_time(
        self, mock_task, mock_langfuse, mock_dataset
    ):
        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,
                metrics=[],
                config={"run_name": "retry-last-attempt"},
                langfuse_client=mock_langfuse,
            )

        evaluator._notify_observer = MagicMock()
        evaluator._compute_metrics = AsyncMock(return_value={})
        evaluator._platform_stream = MagicMock()

        attempt_one = TaskAttemptResult(
            attempt_number=1,
            spans=ItemSpans(trace_id="trace-1", trace_url="url-1"),
            task_started_at_ms=1111,
            latency_s=0.75,
            error="boom",
        )
        attempt_two = TaskAttemptResult(
            attempt_number=2,
            spans=ItemSpans(trace_id="trace-2", trace_url="url-2"),
            task_started_at_ms=2222,
            latency_s=0.25,
            output="final-output",
        )
        evaluator._execute_task = AsyncMock(
            return_value=(attempt_two, [attempt_one, attempt_two], 1)
        )

        item = MagicMock()
        item.input = "test_input"
        item.expected_output = "expected"
        item.id = "item-1"

        tracker = MagicMock()
        result = await evaluator._evaluate_item(0, item, tracker)

        assert result["success"] is True
        assert result["trace_id"] == "trace-2"
        assert result["time"] == pytest.approx(0.25)
        assert result["retry_count"] == 1

        emitted = [call.args for call in evaluator._platform_stream.emit.call_args_list]
        completed = [
            payload for event_type, payload in emitted if event_type == "item_completed"
        ]
        attempt_events = [
            payload
            for event_type, payload in emitted
            if event_type == "item_attempt_finished"
        ]
        assert completed[0]["trace_id"] == "trace-2"
        assert completed[0]["latency_ms"] == pytest.approx(250.0)
        assert attempt_events[0]["attempt_number"] == 2
        assert attempt_events[0]["is_last_attempt"] is True
        assert attempt_events[0]["output"] == "final-output"
        event_types = [event_type for event_type, _ in emitted]
        assert event_types.index("item_attempt_finished") < event_types.index(
            "item_completed"
        )

    @pytest.mark.asyncio
    async def test_evaluate_item_failure_uses_last_failed_attempt_trace_and_time(
        self, mock_task, mock_langfuse, mock_dataset
    ):
        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,
                metrics=[],
                config={"run_name": "retry-last-failure"},
                langfuse_client=mock_langfuse,
            )

        evaluator._notify_observer = MagicMock()
        evaluator._platform_stream = MagicMock()

        attempt_one = TaskAttemptResult(
            attempt_number=1,
            spans=ItemSpans(trace_id="trace-1", trace_url="url-1"),
            task_started_at_ms=1111,
            latency_s=0.75,
            error="boom-1",
        )
        attempt_two = TaskAttemptResult(
            attempt_number=2,
            spans=ItemSpans(trace_id="trace-2", trace_url="url-2"),
            task_started_at_ms=2222,
            latency_s=0.25,
            error="boom-2",
        )
        evaluator._execute_task = AsyncMock(
            return_value=(None, [attempt_one, attempt_two], 1)
        )

        item = MagicMock()
        item.input = "test_input"
        item.expected_output = "expected"
        item.id = "item-1"

        tracker = MagicMock()
        result = await evaluator._evaluate_item(0, item, tracker)

        assert result["_trace_id"] == "trace-2"
        assert result["time"] == pytest.approx(0.25)
        assert result["task_started_at_ms"] == 2222

        emitted = [call.args for call in evaluator._platform_stream.emit.call_args_list]
        failed = [
            payload for event_type, payload in emitted if event_type == "item_failed"
        ]
        attempt_events = [
            payload
            for event_type, payload in emitted
            if event_type == "item_attempt_finished"
        ]
        assert failed[0]["trace_id"] == "trace-2"
        assert failed[0]["latency_ms"] == pytest.approx(250.0)
        assert failed[0]["retry_count"] == 1
        assert attempt_events[0]["trace_id"] == "trace-2"
        assert attempt_events[0]["is_last_attempt"] is True

    def test_sync_threadpool_advisory_emitted_for_high_effective_concurrency(
        self, tmp_path, mock_task, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,world\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        fake_adapter = MagicMock()
        fake_adapter.execution_mode.return_value = "sync-threadpool"
        fake_adapter._warning_callback = None

        with patch("qym.core.evaluator.auto_detect_task", return_value=fake_adapter):
            evaluator = Evaluator(
                task=mock_task,
                dataset=ds,
                metrics=[],
                config={
                    "run_name": "sync-advisory",
                    "task_name": "mock_task",
                    "max_concurrency": 5,
                    "otel_enabled": False,
                },
            )

        evaluator._notify_observer = MagicMock()
        evaluator._maybe_emit_sync_threadpool_advisory(parallel_runs=4)

        evaluator._notify_observer.assert_called_once()
        method = evaluator._notify_observer.call_args.args[0]
        message = evaluator._notify_observer.call_args.kwargs["message"]
        assert method == "on_warning"
        assert "sync-threadpool" in message
        assert "mock_task" in message
        assert "20" in message
        assert "AsyncOpenAI" in message

    def test_sync_threadpool_advisory_not_emitted_below_threshold(
        self, tmp_path, mock_task, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,world\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        fake_adapter = MagicMock()
        fake_adapter.execution_mode.return_value = "sync-threadpool"
        fake_adapter._warning_callback = None

        with patch("qym.core.evaluator.auto_detect_task", return_value=fake_adapter):
            evaluator = Evaluator(
                task=mock_task,
                dataset=ds,
                metrics=[],
                config={
                    "run_name": "sync-advisory-low",
                    "max_concurrency": 5,
                    "otel_enabled": False,
                },
            )

        evaluator._notify_observer = MagicMock()
        evaluator._maybe_emit_sync_threadpool_advisory(parallel_runs=2)

        evaluator._notify_observer.assert_not_called()

    def test_sync_threadpool_advisory_not_emitted_for_async_mode(
        self, tmp_path, mock_task, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,world\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        fake_adapter = MagicMock()
        fake_adapter.execution_mode.return_value = "async"
        fake_adapter._warning_callback = None

        with patch("qym.core.evaluator.auto_detect_task", return_value=fake_adapter):
            evaluator = Evaluator(
                task=mock_task,
                dataset=ds,
                metrics=[],
                config={
                    "run_name": "async-mode",
                    "max_concurrency": 5,
                    "otel_enabled": False,
                },
            )

        evaluator._notify_observer = MagicMock()
        evaluator._maybe_emit_sync_threadpool_advisory(parallel_runs=4)

        evaluator._notify_observer.assert_not_called()

    def test_sync_threadpool_advisory_emitted_once_per_unique_task(
        self, tmp_path, mock_task, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,world\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        fake_adapter = MagicMock()
        fake_adapter.execution_mode.return_value = "sync-threadpool"
        fake_adapter._warning_callback = None

        with patch("qym.core.evaluator.auto_detect_task", return_value=fake_adapter):
            evaluator_one = Evaluator(
                task=mock_task,
                dataset=ds,
                metrics=[],
                config={
                    "run_name": "sync-advisory-one",
                    "task_name": "mock_task",
                    "max_concurrency": 5,
                    "otel_enabled": False,
                },
            )
            evaluator_two = Evaluator(
                task=mock_task,
                dataset=ds,
                metrics=[],
                config={
                    "run_name": "sync-advisory-two",
                    "task_name": "mock_task",
                    "max_concurrency": 5,
                    "otel_enabled": False,
                },
            )

        advisory_registry = set()
        evaluator_one._sync_threadpool_advisory_registry = advisory_registry
        evaluator_two._sync_threadpool_advisory_registry = advisory_registry
        evaluator_one._notify_observer = MagicMock()
        evaluator_two._notify_observer = MagicMock()

        evaluator_one._maybe_emit_sync_threadpool_advisory(parallel_runs=4)
        evaluator_two._maybe_emit_sync_threadpool_advisory(parallel_runs=4)

        evaluator_one._notify_observer.assert_called_once()
        evaluator_two._notify_observer.assert_not_called()
        assert advisory_registry == {"mock_task"}

    def test_sync_threadpool_advisory_emitted_per_distinct_task(
        self, tmp_path, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,world\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        def task_one(_input):
            return "ok"

        def task_two(_input):
            return "ok"

        fake_adapter = MagicMock()
        fake_adapter.execution_mode.return_value = "sync-threadpool"
        fake_adapter._warning_callback = None

        with patch("qym.core.evaluator.auto_detect_task", return_value=fake_adapter):
            evaluator_one = Evaluator(
                task=task_one,
                dataset=ds,
                metrics=[],
                config={
                    "run_name": "sync-task-one",
                    "max_concurrency": 5,
                    "otel_enabled": False,
                },
            )
            evaluator_two = Evaluator(
                task=task_two,
                dataset=ds,
                metrics=[],
                config={
                    "run_name": "sync-task-two",
                    "max_concurrency": 5,
                    "otel_enabled": False,
                },
            )

        advisory_registry = set()
        evaluator_one._sync_threadpool_advisory_registry = advisory_registry
        evaluator_two._sync_threadpool_advisory_registry = advisory_registry
        evaluator_one._notify_observer = MagicMock()
        evaluator_two._notify_observer = MagicMock()

        evaluator_one._maybe_emit_sync_threadpool_advisory(parallel_runs=4)
        evaluator_two._maybe_emit_sync_threadpool_advisory(parallel_runs=4)

        evaluator_one._notify_observer.assert_called_once()
        evaluator_two._notify_observer.assert_called_once()
        # Task names are derived from __qualname__, so the two local
        # functions must register as two distinct advisory entries.
        assert advisory_registry == {task_one.__qualname__, task_two.__qualname__}
        assert len(advisory_registry) == 2

    def test_sync_threadpool_advisory_stays_in_tui_when_dashboard_observer_attached(
        self, tmp_path, mock_task, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,world\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        fake_adapter = MagicMock()
        fake_adapter.execution_mode.return_value = "sync-threadpool"
        fake_adapter._warning_callback = None

        with patch("qym.core.evaluator.auto_detect_task", return_value=fake_adapter):
            evaluator = Evaluator(
                task=mock_task,
                dataset=ds,
                metrics=[],
                config={
                    "run_name": "sync-advisory-tui",
                    "max_concurrency": 5,
                    "otel_enabled": False,
                },
            )

        dashboard = RunDashboard([{"run_id": evaluator.run_name}], enabled=True)
        evaluator.observer = dashboard.create_observer(evaluator.run_name)

        with patch("qym.core.evaluator.logger.warning") as mock_warning:
            evaluator._maybe_emit_sync_threadpool_advisory(parallel_runs=4)

        mock_warning.assert_not_called()
        assert len(dashboard._warnings) == 1
        assert "sync-threadpool" in dashboard._warnings[0]

    def test_sync_threadpool_advisory_logs_when_no_tui_dashboard_is_attached(
        self, tmp_path, mock_task, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,world\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        fake_adapter = MagicMock()
        fake_adapter.execution_mode.return_value = "sync-threadpool"
        fake_adapter._warning_callback = None

        with patch("qym.core.evaluator.auto_detect_task", return_value=fake_adapter):
            evaluator = Evaluator(
                task=mock_task,
                dataset=ds,
                metrics=[],
                config={
                    "run_name": "sync-advisory-log",
                    "max_concurrency": 5,
                    "otel_enabled": False,
                },
            )

        evaluator._notify_observer = MagicMock()

        with patch("qym.core.evaluator.logger.warning") as mock_warning:
            evaluator._maybe_emit_sync_threadpool_advisory(parallel_runs=4)

        mock_warning.assert_called_once()
        evaluator._notify_observer.assert_called_once()

    @pytest.mark.asyncio
    async def test_async_cancellation_emits_stopped_to_platform(
        self, tmp_path, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,world\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        class FakeHandle:
            run_id = "run-123"
            live_url = "http://example/live/run-123"

        class FakePlatformClient:
            def __init__(self, platform_url=None, api_key=None):
                self.platform_url = platform_url
                self.api_key = api_key

            def create_run(self, **kwargs):
                return FakeHandle()

        class FakePlatformEventStream:
            instances = []

            def __init__(self, platform_url=None, api_key=None, run_id=None):
                self.platform_url = platform_url
                self.api_key = api_key
                self.run_id = run_id
                self.events = []
                FakePlatformEventStream.instances.append(self)

            def emit(self, event_type, payload, sync=False):
                self.events.append((event_type, payload, sync))

            def close(self):
                return None

        async def slow_task(_input):
            await asyncio.sleep(5)
            return "ok"

        monkeypatch.setattr("qym.core.evaluator.PlatformClient", FakePlatformClient)
        monkeypatch.setattr(
            "qym.core.evaluator.PlatformEventStream", FakePlatformEventStream
        )

        evaluator = Evaluator(
            task=slow_task,
            dataset=ds,
            metrics=[],
            config={
                "run_name": "async-cancel",
                "task_name": "slow_task",
                "output_dir": str(tmp_path / "results"),
                "max_concurrency": 1,
                "otel_enabled": False,
                "platform_api_key": "test-key",
                "platform_url": "http://example",
            },
        )

        task = asyncio.create_task(evaluator.arun(show_tui=False, auto_save=False))
        await asyncio.sleep(0.05)
        task.cancel()

        with pytest.raises(asyncio.CancelledError):
            await task

        assert FakePlatformEventStream.instances
        events = FakePlatformEventStream.instances[-1].events
        completed = [
            payload
            for event_type, payload, _sync in events
            if event_type == "run_completed"
        ]
        assert completed
        assert completed[-1]["final_status"] == "STOPPED"

    @pytest.mark.asyncio
    async def test_should_stop_before_first_item_emits_stopped_without_item_failures(
        self, tmp_path, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\none,one\ntwo,two\nthree,three\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        class FakeHandle:
            run_id = "run-stop-before"
            live_url = "http://example/live/run-stop-before"

        class FakePlatformClient:
            def __init__(self, platform_url=None, api_key=None):
                self.platform_url = platform_url
                self.api_key = api_key

            def create_run(self, **kwargs):
                return FakeHandle()

        class FakePlatformEventStream:
            instances = []

            def __init__(self, platform_url=None, api_key=None, run_id=None):
                self.events = []
                FakePlatformEventStream.instances.append(self)

            def emit(self, event_type, payload, sync=False):
                self.events.append((event_type, payload, sync))

            def close(self):
                return None

        calls = 0

        async def task(_input):
            nonlocal calls
            calls += 1
            return "ok"

        monkeypatch.setattr("qym.core.evaluator.PlatformClient", FakePlatformClient)
        monkeypatch.setattr(
            "qym.core.evaluator.PlatformEventStream", FakePlatformEventStream
        )

        evaluator = Evaluator(
            task=task,
            dataset=ds,
            metrics=[],
            config={
                "run_name": "stop-before",
                "task_name": "stop_before_task",
                "output_dir": str(tmp_path / "results"),
                "max_concurrency": 2,
                "otel_enabled": False,
                "platform_api_key": "test-key",
                "platform_url": "http://example",
                "should_stop": lambda: True,
            },
        )

        result = await evaluator.arun(show_tui=False, auto_save=False)

        assert calls == 0
        assert result.interrupted is True
        assert result.results == {}
        assert result.errors == {}
        events = FakePlatformEventStream.instances[-1].events
        assert not [event for event in events if event[0] == "item_failed"]
        completed = [
            payload
            for event_type, payload, _sync in events
            if event_type == "run_completed"
        ]
        assert completed[-1]["final_status"] == "STOPPED"

    @pytest.mark.asyncio
    async def test_should_stop_mid_run_leaves_pending_items_unfailed(
        self, tmp_path, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text(
            "q,a\none,one\ntwo,two\nthree,three\nfour,four\nfive,five\n",
            encoding="utf-8",
        )
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        stop = False
        calls = 0

        async def task(value):
            nonlocal stop, calls
            calls += 1
            stop = True
            await asyncio.sleep(0)
            return value

        evaluator = Evaluator(
            task=task,
            dataset=ds,
            metrics=[],
            config={
                "run_name": "stop-mid-run",
                "task_name": "stop_mid_run_task",
                "output_dir": str(tmp_path / "results"),
                "max_concurrency": 1,
                "otel_enabled": False,
                "should_stop": lambda: stop,
            },
        )

        result = await evaluator.arun(show_tui=False, auto_save=False)

        assert calls == 1
        assert result.interrupted is True
        assert len(result.results) == 1
        assert result.errors == {}

    @pytest.mark.asyncio
    async def test_observer_run_start_includes_qym_url(self, tmp_path, monkeypatch):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,hello\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        class FakeHandle:
            run_id = "platform-run-1"
            live_url = "http://example/live/platform-run-1"

        class FakePlatformClient:
            def __init__(self, platform_url=None, api_key=None):
                self.platform_url = platform_url
                self.api_key = api_key

            def create_run(self, **kwargs):
                return FakeHandle()

        class FakePlatformEventStream:
            def __init__(self, platform_url=None, api_key=None, run_id=None):
                self.platform_url = platform_url
                self.api_key = api_key
                self.run_id = run_id

            def emit(self, event_type, payload, sync=False):
                return None

            def close(self):
                return None

        snapshots = []
        monkeypatch.setattr("qym.core.evaluator.PlatformClient", FakePlatformClient)
        monkeypatch.setattr(
            "qym.core.evaluator.PlatformEventStream", FakePlatformEventStream
        )

        evaluator = Evaluator(
            task=lambda input_data: input_data,
            dataset=ds,
            metrics=[],
            config={
                "run_name": "url-start",
                "task_name": "echo_task",
                "output_dir": str(tmp_path / "results"),
                "otel_enabled": False,
                "platform_api_key": "test-key",
                "platform_url": "http://example",
            },
            progress_callback=snapshots.append,
        )

        await evaluator.arun(show_tui=False, auto_save=False)

        run_start = next(
            snapshot for snapshot in snapshots if snapshot.event == "run_start"
        )
        assert run_start.run_info["qym_url"] == "http://example/live/platform-run-1"
        assert run_start.run_info["html_url"] == "http://example/live/platform-run-1"
        assert run_start.run_info["platform_run_id"] == "platform-run-1"

    @pytest.mark.asyncio
    async def test_platform_create_run_timeout_does_not_abort_eval(
        self, tmp_path, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,hello\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        class SlowPlatformClient:
            def __init__(self, platform_url=None, api_key=None):
                self.platform_url = platform_url
                self.api_key = api_key

            def create_run(self, **kwargs):
                raise TimeoutError("timed out")

        snapshots = []
        monkeypatch.setattr("qym.core.evaluator.PlatformClient", SlowPlatformClient)

        evaluator = Evaluator(
            task=lambda input_data: input_data,
            dataset=ds,
            metrics=[],
            config={
                "run_name": "platform-timeout",
                "task_name": "echo_task",
                "output_dir": str(tmp_path / "results"),
                "otel_enabled": False,
                "platform_api_key": "test-key",
                "platform_url": "http://example",
                "platform_timeout": 0.01,
            },
            progress_callback=snapshots.append,
        )

        result = await evaluator.arun(show_tui=False, auto_save=False)

        assert result.total_items == 1
        assert not getattr(result, "html_url", None)
        warnings = [snapshot for snapshot in snapshots if snapshot.event == "warning"]
        assert warnings
        assert "Platform live UI disabled" in warnings[0].message
        run_start = next(
            snapshot for snapshot in snapshots if snapshot.event == "run_start"
        )
        assert run_start.run_info["trace"]["destinations"]["platform"] is False
        assert "platform_error" in run_start.run_info["trace"]["destinations"]

    @pytest.mark.asyncio
    async def test_observer_metric_and_item_events_include_timings(
        self, tmp_path, monkeypatch
    ):
        p = tmp_path / "qa.csv"
        p.write_text("q,a\nhello,hello\n", encoding="utf-8")
        ds = CsvDataset(p, input_col="q", expected_col="a")

        monkeypatch.delenv("LANGFUSE_PUBLIC_KEY", raising=False)
        monkeypatch.delenv("LANGFUSE_SECRET_KEY", raising=False)

        def exact(output, expected):
            return 1.0 if output == expected else 0.0

        snapshots = []
        evaluator = Evaluator(
            task=lambda input_data: input_data,
            dataset=ds,
            metrics=[exact],
            config={
                "run_name": "observer-timings",
                "task_name": "echo_task",
                "output_dir": str(tmp_path / "results"),
                "otel_enabled": False,
            },
            progress_callback=snapshots.append,
        )

        await evaluator.arun(show_tui=False, auto_save=False)

        metric_result = next(
            snapshot for snapshot in snapshots if snapshot.event == "metric_result"
        )
        item_complete = next(
            snapshot for snapshot in snapshots if snapshot.event == "item_complete"
        )

        assert metric_result.metadata["duration_ms"] >= 0.0
        assert metric_result.metadata["duration_seconds"] >= 0.0
        assert (
            metric_result.metadata["started_at_ms"]
            <= metric_result.metadata["completed_at_ms"]
        )
        assert metric_result.metadata["status"] == "completed"

        assert item_complete.result["task_time_ms"] >= 0.0
        assert (
            item_complete.result["latency_ms"] == item_complete.result["task_time_ms"]
        )
        assert (
            item_complete.result["total_time_ms"]
            >= item_complete.result["task_time_ms"]
        )
        assert (
            item_complete.result["item_started_at_ms"]
            <= item_complete.result["item_completed_at_ms"]
        )
        assert item_complete.result["scores"]


class TestSyncMetricOffloading:
    @pytest.mark.asyncio
    async def test_sync_metric_runs_off_the_event_loop_thread(
        self, mock_task, mock_dataset
    ):
        """Sync metrics must run in the thread pool: calling them inline blocks
        the event loop and inflates the measured task latency of every other
        in-flight item."""
        import threading

        loop_thread = threading.get_ident()
        metric_thread = {}

        def slow_sync_metric(output, expected):
            metric_thread["ident"] = threading.get_ident()
            return 1.0

        with patch("qym.core.evaluator.auto_detect_task"):
            evaluator = Evaluator(
                task=mock_task,
                dataset=mock_dataset,
                metrics=[slow_sync_metric],
                config={"run_name": "test-run"},
            )

        result = await evaluator._compute_metric(slow_sync_metric, "out", "exp")

        assert result == 1.0
        assert metric_thread["ident"] != loop_thread

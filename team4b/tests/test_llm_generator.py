"""Focused tests for Task 6.1's LLMGenerator.

Scope: unit tests for prompt construction, grounding instructions,
insufficient-context behavior, error/LLMUnavailable mapping, malformed
response handling, and configuration plumbing. Explicitly NOT Task 6.2's
Property 8 (prompt completeness) -- these are ordinary example-based
unit tests, not the formal property test, and are not labeled as such.

ANTI-CIRCULARITY: expected prompt contents are asserted via membership
checks (`assert query in prompt`, `assert chunk.text in prompt`, ...)
against values the test itself independently generated -- never by
calling `build_prompt()` a second time to produce the "expected" prompt
for comparison against its own first call.
"""

from __future__ import annotations

from typing import Any

import pytest

from app.core.config import Settings
from app.models.retrieval import RetrievalResult
from app.services.conversation import ConversationTurn
from app.services.llm_generator import (
    INSUFFICIENT_CONTEXT_MESSAGE,
    LLMGenerator,
    LLMUnavailableError,
    build_prompt,
)
from tests.fakes import FakeLLMClient


def _settings(**overrides: Any) -> Settings:
    return Settings(_env_file=None, **overrides)  # type: ignore[call-arg]


def _generator(llm_client: FakeLLMClient | None = None, **settings_overrides: Any) -> tuple[LLMGenerator, FakeLLMClient]:
    client = llm_client or FakeLLMClient()
    generator = LLMGenerator(settings=_settings(**settings_overrides), llm_client=client)
    return generator, client


def _chunk(chunk_id: str, text: str) -> RetrievalResult:
    return RetrievalResult(chunk_id=chunk_id, text=text, relevance_score=0.9, metadata={})


def _turn(role: str, content: str, timestamp: float = 1.0) -> ConversationTurn:
    return ConversationTurn(role=role, content=content, timestamp=timestamp)  # type: ignore[arg-type]


# ---------------------------------------------------------------------------
# 1. Successful generation
# ---------------------------------------------------------------------------


class TestSuccessfulGeneration:
    def test_returns_the_llm_clients_response(self):
        generator, _client = _generator(llm_client=FakeLLMClient(response="Paris is the capital of France."))

        answer = generator.generate("What is the capital of France?", [_chunk("c1", "France's capital is Paris.")])

        assert answer == "Paris is the capital of France."

    def test_generate_is_called_exactly_once_per_call(self):
        generator, client = _generator()

        generator.generate("query", [_chunk("c1", "some context")])

        assert len(client.calls) == 1


# ---------------------------------------------------------------------------
# 2-5. Prompt construction: query, all chunks, history, clear separation
# ---------------------------------------------------------------------------


class TestPromptConstruction:
    def test_query_appears_in_prompt(self):
        generator, client = _generator()

        generator.generate("What is retrieval augmented generation?", [_chunk("c1", "context text")])

        assert "What is retrieval augmented generation?" in client.calls[0]["prompt"]

    def test_all_supplied_chunk_texts_appear_in_prompt_not_just_the_first(self):
        chunks = [
            _chunk("c1", "Alpha content unique marker AAA"),
            _chunk("c2", "Beta content unique marker BBB"),
            _chunk("c3", "Gamma content unique marker CCC"),
        ]
        generator, client = _generator()

        generator.generate("query", chunks)

        prompt = client.calls[0]["prompt"]
        for chunk in chunks:
            assert chunk.text in prompt

    def test_ten_chunks_are_all_included(self):
        chunks = [_chunk(f"c{i}", f"unique chunk content marker {i}") for i in range(10)]
        generator, client = _generator()

        generator.generate("query", chunks)

        prompt = client.calls[0]["prompt"]
        for chunk in chunks:
            assert chunk.text in prompt

    def test_conversation_history_appears_in_prompt(self):
        history = [_turn("user", "What is RAG?"), _turn("assistant", "RAG stands for Retrieval-Augmented Generation.")]
        generator, client = _generator()

        generator.generate("Tell me more", [_chunk("c1", "context")], conversation_history=history)

        prompt = client.calls[0]["prompt"]
        assert "What is RAG?" in prompt
        assert "RAG stands for Retrieval-Augmented Generation." in prompt

    def test_history_ordering_is_preserved_in_prompt(self):
        history = [
            _turn("user", "first turn marker AAA"),
            _turn("assistant", "second turn marker BBB"),
            _turn("user", "third turn marker CCC"),
        ]
        generator, client = _generator()

        generator.generate("query", [_chunk("c1", "context")], conversation_history=history)

        prompt = client.calls[0]["prompt"]
        # Independent oracle: derive expected relative order directly
        # from the generated/supplied history, not from re-invoking
        # build_prompt.
        positions = [prompt.index(turn.content) for turn in history]
        assert positions == sorted(positions)

    def test_chunk_ordering_is_preserved_in_prompt(self):
        chunks = [_chunk("c1", "first marker AAA"), _chunk("c2", "second marker BBB"), _chunk("c3", "third marker CCC")]
        generator, client = _generator()

        generator.generate("query", chunks)

        prompt = client.calls[0]["prompt"]
        positions = [prompt.index(chunk.text) for chunk in chunks]
        assert positions == sorted(positions)

    def test_prompt_separates_context_history_and_query_sections(self):
        generator, client = _generator()

        generator.generate("query", [_chunk("c1", "context")], conversation_history=[_turn("user", "hi")])

        prompt = client.calls[0]["prompt"]
        assert "Context" in prompt
        assert "Conversation History" in prompt
        assert "Current Question" in prompt
        # Sections appear in a sensible, non-interleaved order.
        assert prompt.index("Context") < prompt.index("Conversation History") < prompt.index("Current Question")

    def test_no_history_supplied_does_not_crash_and_still_includes_query(self):
        generator, client = _generator()

        answer = generator.generate("query", [_chunk("c1", "context")])

        assert answer  # generation still succeeds
        assert "query" in client.calls[0]["prompt"]

    def test_build_prompt_is_a_pure_function_usable_independently(self):
        # Exercising build_prompt directly (not just through generate())
        # to confirm it's a standalone, independently testable unit.
        prompt = build_prompt("my query", [_chunk("c1", "my context")], [_turn("user", "my history")])

        assert "my query" in prompt
        assert "my context" in prompt
        assert "my history" in prompt


# ---------------------------------------------------------------------------
# Grounding instructions present
# ---------------------------------------------------------------------------


class TestGroundingInstructions:
    def test_prompt_instructs_use_of_only_provided_context(self):
        generator, client = _generator()

        generator.generate("query", [_chunk("c1", "context")])

        prompt = client.calls[0]["prompt"].lower()
        assert "only" in prompt
        assert "outside knowledge" in prompt

    def test_prompt_instructs_against_fabricating_citations(self):
        generator, client = _generator()

        generator.generate("query", [_chunk("c1", "context")])

        prompt = client.calls[0]["prompt"].lower()
        assert "fabricate" in prompt or "invent" in prompt

    def test_no_source_attribution_metadata_is_fabricated_by_generator(self):
        """LLMGenerator's return value is the bare answer string -- it
        never adds chunk_ids, page numbers, timestamps, or relevance
        scores of its own. Source attribution assembly is explicitly a
        later task's responsibility (not Task 6.1's)."""

        chunk = RetrievalResult(chunk_id="secret-id-123", text="context", relevance_score=0.42, metadata={"page_number": 7})
        generator, client = _generator(llm_client=FakeLLMClient(response="The answer is 42."))

        answer = generator.generate("query", [chunk])

        assert answer == "The answer is 42."
        assert "secret-id-123" not in answer
        assert "0.42" not in answer


# ---------------------------------------------------------------------------
# 6-7. Empty context / insufficient-context behavior
# ---------------------------------------------------------------------------


class TestInsufficientContext:
    def test_empty_retrieved_results_returns_fixed_insufficient_context_message(self):
        generator, client = _generator()

        answer = generator.generate("query", [])

        assert answer == INSUFFICIENT_CONTEXT_MESSAGE

    def test_empty_retrieved_results_never_calls_the_llm_client(self):
        """The critical distinction the task brief calls out explicitly:
        "retriever returned zero chunks" must never reach the LLM at
        all, so it can never hallucinate an answer despite grounding
        instructions."""

        generator, client = _generator()

        generator.generate("query", [])

        assert client.calls == []

    def test_insufficient_context_message_is_deterministic_across_calls(self):
        generator, _client = _generator()

        first = generator.generate("query one", [])
        second = generator.generate("completely different query", [])

        assert first == second == INSUFFICIENT_CONTEXT_MESSAGE


# ---------------------------------------------------------------------------
# 8. Ollama/network failure maps to LLMUnavailable
# ---------------------------------------------------------------------------


class TestLLMUnavailableMapping:
    def test_client_connection_failure_raises_llm_unavailable(self):
        generator, _client = _generator(llm_client=FakeLLMClient(raise_error=ConnectionError("refused")))

        with pytest.raises(LLMUnavailableError):
            generator.generate("query", [_chunk("c1", "context")])

    def test_client_timeout_raises_llm_unavailable(self):
        generator, _client = _generator(llm_client=FakeLLMClient(raise_error=TimeoutError("timed out")))

        with pytest.raises(LLMUnavailableError):
            generator.generate("query", [_chunk("c1", "context")])

    def test_raw_client_exception_is_not_leaked_to_the_caller(self):
        generator, _client = _generator(llm_client=FakeLLMClient(raise_error=ConnectionError("raw error")))

        with pytest.raises(LLMUnavailableError) as exc_info:
            generator.generate("query", [_chunk("c1", "context")])

        assert not isinstance(exc_info.value, ConnectionError)

    def test_llm_unavailable_error_preserves_original_exception_for_debugging(self):
        original = ConnectionError("refused")
        generator, _client = _generator(llm_client=FakeLLMClient(raise_error=original))

        with pytest.raises(LLMUnavailableError) as exc_info:
            generator.generate("query", [_chunk("c1", "context")])

        assert exc_info.value.last_error is original

    def test_transient_failure_then_recovery_is_not_retried_automatically(self):
        # No retries are implemented for Ollama (documented decision) --
        # a single failure raises immediately, even if a subsequent call
        # would have succeeded.
        client = FakeLLMClient(fail_times=1, response="would have worked")
        generator, _client = _generator(llm_client=client)

        with pytest.raises(LLMUnavailableError):
            generator.generate("query", [_chunk("c1", "context")])

        assert len(client.calls) == 1  # exactly one attempt, no retry


# ---------------------------------------------------------------------------
# 9-10. Malformed / empty Ollama response handling (via RealOllamaClient)
# ---------------------------------------------------------------------------


class _FakeHTTPXResponse:
    def __init__(self, status_code: int, json_data: Any = None, json_error: bool = False, text: str = "") -> None:
        self.status_code = status_code
        self._json_data = json_data
        self._json_error = json_error
        self.text = text

    def json(self) -> Any:
        if self._json_error:
            raise ValueError("not valid json")
        return self._json_data


class TestRealOllamaClientResponseHandling:
    def _client_with_stubbed_post(self, monkeypatch: pytest.MonkeyPatch, response: _FakeHTTPXResponse) -> Any:
        from app.services import llm_generator as llm_generator_module

        real_client = llm_generator_module.RealOllamaClient(base_url="http://fake-ollama:11434")

        import httpx

        monkeypatch.setattr(httpx, "post", lambda *args, **kwargs: response)
        return real_client

    def test_non_200_status_raises_llm_unavailable(self, monkeypatch: pytest.MonkeyPatch) -> None:
        client = self._client_with_stubbed_post(monkeypatch, _FakeHTTPXResponse(status_code=500, text="server error"))

        with pytest.raises(LLMUnavailableError):
            client.generate(model="llama3", prompt="hi", timeout=15.0)

    def test_non_json_body_raises_llm_unavailable(self, monkeypatch: pytest.MonkeyPatch) -> None:
        client = self._client_with_stubbed_post(monkeypatch, _FakeHTTPXResponse(status_code=200, json_error=True))

        with pytest.raises(LLMUnavailableError):
            client.generate(model="llama3", prompt="hi", timeout=15.0)

    def test_missing_response_field_raises_llm_unavailable(self, monkeypatch: pytest.MonkeyPatch) -> None:
        client = self._client_with_stubbed_post(monkeypatch, _FakeHTTPXResponse(status_code=200, json_data={"done": True}))

        with pytest.raises(LLMUnavailableError):
            client.generate(model="llama3", prompt="hi", timeout=15.0)

    def test_non_string_response_field_raises_llm_unavailable(self, monkeypatch: pytest.MonkeyPatch) -> None:
        client = self._client_with_stubbed_post(
            monkeypatch, _FakeHTTPXResponse(status_code=200, json_data={"response": 12345})
        )

        with pytest.raises(LLMUnavailableError):
            client.generate(model="llama3", prompt="hi", timeout=15.0)

    def test_json_body_that_is_not_an_object_raises_llm_unavailable(self, monkeypatch: pytest.MonkeyPatch) -> None:
        client = self._client_with_stubbed_post(monkeypatch, _FakeHTTPXResponse(status_code=200, json_data=[1, 2, 3]))

        with pytest.raises(LLMUnavailableError):
            client.generate(model="llama3", prompt="hi", timeout=15.0)

    def test_valid_empty_string_response_is_passed_through_not_treated_as_an_error(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        client = self._client_with_stubbed_post(monkeypatch, _FakeHTTPXResponse(status_code=200, json_data={"response": ""}))

        answer = client.generate(model="llama3", prompt="hi", timeout=15.0)

        assert answer == ""

    def test_valid_non_empty_response_is_extracted_correctly(self, monkeypatch: pytest.MonkeyPatch) -> None:
        client = self._client_with_stubbed_post(
            monkeypatch, _FakeHTTPXResponse(status_code=200, json_data={"response": "the generated answer", "done": True})
        )

        answer = client.generate(model="llama3", prompt="hi", timeout=15.0)

        assert answer == "the generated answer"


class TestGeneratorHandlesEmptyModelResponse:
    def test_empty_string_answer_from_client_is_returned_not_replaced(self):
        generator, _client = _generator(llm_client=FakeLLMClient(response=""))

        answer = generator.generate("query", [_chunk("c1", "context")])

        assert answer == ""  # passed through, not silently mutated into something else

    def test_non_string_answer_from_a_misbehaving_client_raises_llm_unavailable(self):
        class _BadClient:
            def generate(self, model: str, prompt: str, timeout: float, *, num_gpu: int | None = None, num_predict: int | None = None) -> str:
                return None  # type: ignore[return-value]

        generator = LLMGenerator(settings=_settings(), llm_client=_BadClient())

        with pytest.raises(LLMUnavailableError):
            generator.generate("query", [_chunk("c1", "context")])


# ---------------------------------------------------------------------------
# 11-13. Configuration plumbing: model, endpoint, timeout
# ---------------------------------------------------------------------------


class TestConfigurationPlumbing:
    def test_configured_model_is_passed_to_the_llm_client(self):
        generator, client = _generator(ollama_model_name="custom-model-name")

        generator.generate("query", [_chunk("c1", "context")])

        assert client.calls[0]["model"] == "custom-model-name"

    def test_default_model_is_llama3(self):
        generator, client = _generator()  # no override -- uses the real default

        generator.generate("query", [_chunk("c1", "context")])

        assert client.calls[0]["model"] == "llama3"

    def test_configured_timeout_is_passed_to_the_llm_client(self):
        generator, client = _generator(llm_generation_timeout_seconds=42.0)

        generator.generate("query", [_chunk("c1", "context")])

        assert client.calls[0]["timeout"] == 42.0

    def test_default_timeout_is_15_seconds(self):
        generator, client = _generator()  # no override -- uses the real default

        generator.generate("query", [_chunk("c1", "context")])

        assert client.calls[0]["timeout"] == 15.0

    def test_real_ollama_client_uses_configured_base_url(self):
        from app.services.llm_generator import RealOllamaClient

        client = RealOllamaClient(base_url="http://custom-ollama-host:9999")

        assert client._base_url == "http://custom-ollama-host:9999"

    def test_real_ollama_client_strips_trailing_slash_from_base_url(self):
        from app.services.llm_generator import RealOllamaClient

        client = RealOllamaClient(base_url="http://custom-ollama-host:9999/")

        assert client._base_url == "http://custom-ollama-host:9999"

    def test_llm_generator_constructs_real_client_lazily_from_settings(self):
        # Constructing an LLMGenerator with no injected client must not
        # itself attempt any network I/O -- only calling generate()
        # would (and that's covered by TestRealOllamaClientResponseHandling
        # with a stubbed httpx.post, never a live server).
        generator = LLMGenerator(settings=_settings(ollama_url="http://unreachable-host-for-this-test:11434"))

        assert generator is not None  # construction alone must not raise/connect


# ---------------------------------------------------------------------------
# Task 10.1: check_health()
# ---------------------------------------------------------------------------


class TestRealOllamaClientCheckHealth:
    def test_returns_true_on_200_response(self, monkeypatch: pytest.MonkeyPatch) -> None:
        from app.services.llm_generator import RealOllamaClient

        client = RealOllamaClient(base_url="http://fake-ollama:11434")
        calls: list[tuple[str, float]] = []

        import httpx

        def fake_get(url: str, timeout: float) -> Any:
            calls.append((url, timeout))
            return _FakeHTTPXResponse(status_code=200)

        monkeypatch.setattr(httpx, "get", fake_get)

        assert client.check_health() is True
        assert calls == [("http://fake-ollama:11434/api/tags", 5.0)]

    def test_returns_false_on_non_200_response(self, monkeypatch: pytest.MonkeyPatch) -> None:
        from app.services.llm_generator import RealOllamaClient

        client = RealOllamaClient(base_url="http://fake-ollama:11434")

        import httpx

        monkeypatch.setattr(httpx, "get", lambda url, timeout: _FakeHTTPXResponse(status_code=503))

        assert client.check_health() is False

    def test_returns_false_on_connection_error(self, monkeypatch: pytest.MonkeyPatch) -> None:
        from app.services.llm_generator import RealOllamaClient

        client = RealOllamaClient(base_url="http://fake-ollama:11434")

        import httpx

        def raise_connect_error(url: str, timeout: float) -> Any:
            raise httpx.ConnectError("connection refused")

        monkeypatch.setattr(httpx, "get", raise_connect_error)

        assert client.check_health() is False

    def test_never_calls_the_generate_endpoint(self, monkeypatch: pytest.MonkeyPatch) -> None:
        # Explicit proof that check_health() never triggers a real
        # generation call: stubbing httpx.post to raise means the test
        # would fail loudly if check_health() ever called generate()/
        # POST /api/generate internally.
        from app.services.llm_generator import RealOllamaClient

        client = RealOllamaClient(base_url="http://fake-ollama:11434")

        import httpx

        def fail_if_post_is_called(*args: Any, **kwargs: Any) -> Any:
            raise AssertionError("check_health() must never call httpx.post (a generation call)")

        monkeypatch.setattr(httpx, "post", fail_if_post_is_called)
        monkeypatch.setattr(httpx, "get", lambda url, timeout: _FakeHTTPXResponse(status_code=200))

        assert client.check_health() is True  # would have raised above if generate() had been triggered

    def test_does_not_require_a_model_argument(self) -> None:
        # Sanity check: check_health() takes no arguments beyond self --
        # it is not parameterized per-model the way generate() is.
        import inspect

        from app.services.llm_generator import RealOllamaClient

        signature = inspect.signature(RealOllamaClient.check_health)
        assert list(signature.parameters.keys()) == ["self"]


class TestLLMGeneratorCheckHealth:
    def test_delegates_to_the_injected_clients_check_health(self):
        client = FakeLLMClient(health_result=True)
        generator = LLMGenerator(settings=_settings(), llm_client=client)

        assert generator.check_health() is True
        assert client.check_health_calls == 1

    def test_returns_false_when_client_reports_unhealthy(self):
        client = FakeLLMClient(health_result=False)
        generator = LLMGenerator(settings=_settings(), llm_client=client)

        assert generator.check_health() is False

    def test_returns_false_when_client_raises(self):
        class _RaisingHealthClient:
            def generate(self, model: str, prompt: str, timeout: float, *, num_gpu: int | None = None, num_predict: int | None = None) -> str:
                return "unused"

            def check_health(self) -> bool:
                raise ConnectionError("down")

        generator = LLMGenerator(settings=_settings(), llm_client=_RaisingHealthClient())

        assert generator.check_health() is False

    def test_never_calls_generate(self):
        client = FakeLLMClient(health_result=True)
        generator = LLMGenerator(settings=_settings(), llm_client=client)

        generator.check_health()

        assert client.calls == []  # generate() was never invoked


class TestM6OllamaGpuReliabilityOption:
    """MVP M6 reliability correction -- evidence: a real Ollama-side CUDA
    initialization crash (exit status 0xc0000409) on one specific local
    Windows/RTX 3050 environment, under Ollama's own default GPU/CPU
    allocation. Settings.ollama_num_gpu is an OPT-IN escape hatch, never
    on by default."""

    def test_num_gpu_is_none_by_default_and_is_still_passed_through_explicitly(self):
        generator, client = _generator()  # no override -- real default settings

        generator.generate("query", [_chunk("c1", "context")])

        assert client.calls[0]["num_gpu"] is None

    def test_configured_num_gpu_reaches_the_client(self):
        generator, client = _generator(ollama_num_gpu=0)

        generator.generate("query", [_chunk("c1", "context")])

        assert client.calls[0]["num_gpu"] == 0

    def test_real_ollama_client_omits_options_entirely_when_num_gpu_is_none(self, monkeypatch):
        from app.services.llm_generator import RealOllamaClient

        captured: dict[str, Any] = {}

        class _FakeResponse:
            status_code = 200

            def json(self):
                return {"response": "ok"}

        def _fake_post(url, json, timeout):
            captured["json"] = json
            return _FakeResponse()

        monkeypatch.setattr("httpx.post", _fake_post)
        client = RealOllamaClient(base_url="http://localhost:11434")

        client.generate(model="llama3", prompt="hello", timeout=15.0)

        assert "options" not in captured["json"]

    def test_real_ollama_client_includes_num_gpu_option_when_configured(self, monkeypatch):
        from app.services.llm_generator import RealOllamaClient

        captured: dict[str, Any] = {}

        class _FakeResponse:
            status_code = 200

            def json(self):
                return {"response": "ok"}

        def _fake_post(url, json, timeout):
            captured["json"] = json
            return _FakeResponse()

        monkeypatch.setattr("httpx.post", _fake_post)
        client = RealOllamaClient(base_url="http://localhost:11434")

        client.generate(model="llama3", prompt="hello", timeout=15.0, num_gpu=0)

        assert captured["json"]["options"] == {"num_gpu": 0}

    def test_default_ollama_num_gpu_setting_is_none(self):
        generator, client = _generator()
        assert generator._settings.ollama_num_gpu is None


class TestM6OllamaNumPredictOption:
    """MVP M6 local-stabilization correction -- an opt-in output-length
    ceiling, following the exact same pattern established for
    ollama_num_gpu."""

    def test_default_ollama_num_predict_setting_is_none(self):
        generator, _client = _generator()
        assert generator._settings.ollama_num_predict is None

    def test_num_predict_is_none_by_default_and_is_still_passed_through_explicitly(self):
        generator, client = _generator()

        generator.generate("query", [_chunk("c1", "context")])

        assert client.calls[0]["num_predict"] is None

    def test_configured_num_predict_reaches_the_client(self):
        generator, client = _generator(ollama_num_predict=1024)

        generator.generate("query", [_chunk("c1", "context")])

        assert client.calls[0]["num_predict"] == 1024

    def test_real_ollama_client_omits_options_entirely_when_both_num_gpu_and_num_predict_are_none(self, monkeypatch):
        from app.services.llm_generator import RealOllamaClient

        captured: dict[str, Any] = {}

        class _FakeResponse:
            status_code = 200

            def json(self):
                return {"response": "ok"}

        def _fake_post(url, json, timeout):
            captured["json"] = json
            return _FakeResponse()

        monkeypatch.setattr("httpx.post", _fake_post)
        client = RealOllamaClient(base_url="http://localhost:11434")

        client.generate(model="llama3", prompt="hello", timeout=15.0)

        assert "options" not in captured["json"]

    def test_real_ollama_client_includes_num_predict_option_when_configured_alone(self, monkeypatch):
        from app.services.llm_generator import RealOllamaClient

        captured: dict[str, Any] = {}

        class _FakeResponse:
            status_code = 200

            def json(self):
                return {"response": "ok"}

        def _fake_post(url, json, timeout):
            captured["json"] = json
            return _FakeResponse()

        monkeypatch.setattr("httpx.post", _fake_post)
        client = RealOllamaClient(base_url="http://localhost:11434")

        client.generate(model="llama3", prompt="hello", timeout=15.0, num_predict=1024)

        assert captured["json"]["options"] == {"num_predict": 1024}

    def test_real_ollama_client_includes_both_options_together_when_both_configured(self, monkeypatch):
        from app.services.llm_generator import RealOllamaClient

        captured: dict[str, Any] = {}

        class _FakeResponse:
            status_code = 200

            def json(self):
                return {"response": "ok"}

        def _fake_post(url, json, timeout):
            captured["json"] = json
            return _FakeResponse()

        monkeypatch.setattr("httpx.post", _fake_post)
        client = RealOllamaClient(base_url="http://localhost:11434")

        client.generate(model="llama3", prompt="hello", timeout=15.0, num_gpu=0, num_predict=1024)

        assert captured["json"]["options"] == {"num_gpu": 0, "num_predict": 1024}

    def test_existing_num_gpu_only_behavior_is_unaffected_by_this_addition(self, monkeypatch):
        from app.services.llm_generator import RealOllamaClient

        captured: dict[str, Any] = {}

        class _FakeResponse:
            status_code = 200

            def json(self):
                return {"response": "ok"}

        def _fake_post(url, json, timeout):
            captured["json"] = json
            return _FakeResponse()

        monkeypatch.setattr("httpx.post", _fake_post)
        client = RealOllamaClient(base_url="http://localhost:11434")

        client.generate(model="llama3", prompt="hello", timeout=15.0, num_gpu=0)

        assert captured["json"]["options"] == {"num_gpu": 0}


class TestM6ContextProvenanceLabeling:
    """MVP M6 correction -- the LLM must be told what kind of source,
    and which specific source, each context entry came from, using
    fields already present on RetrievalResult.metadata."""

    def _youtube_chunk(self, text: str, *, video_title=None, start=None, end=None) -> RetrievalResult:
        metadata: dict[str, Any] = {"source_type": "video"}
        if video_title is not None:
            metadata["document_title"] = video_title
            metadata["video_title"] = video_title
        if start is not None:
            metadata["start_timestamp"] = start
        if end is not None:
            metadata["end_timestamp"] = end
        return RetrievalResult(chunk_id="c1", text=text, relevance_score=0.9, metadata=metadata)

    def _pdf_chunk(self, text: str, *, title=None, page=None) -> RetrievalResult:
        metadata: dict[str, Any] = {"source_type": "document"}
        if title is not None:
            metadata["document_title"] = title
        if page is not None:
            metadata["page_number"] = page
        return RetrievalResult(chunk_id="c1", text=text, relevance_score=0.9, metadata=metadata)

    def test_youtube_context_includes_source_provenance(self):
        chunk = self._youtube_chunk("FCFS scheduling content.", video_title="OS Lecture", start=1191.0)
        prompt = build_prompt("q", [chunk], [])
        assert "YouTube" in prompt
        assert "FCFS scheduling content." in prompt  # original text still verbatim

    def test_youtube_timestamp_is_included_when_present(self):
        chunk = self._youtube_chunk("content", start=1191.0)
        prompt = build_prompt("q", [chunk], [])
        assert "19:51" in prompt

    def test_youtube_timestamp_range_included_when_both_present(self):
        chunk = self._youtube_chunk("content", start=1191.0, end=1203.0)
        prompt = build_prompt("q", [chunk], [])
        assert "19:51" in prompt and "20:03" in prompt

    def test_youtube_video_title_included_when_present(self):
        chunk = self._youtube_chunk("content", video_title="Operating Systems Lecture", start=60.0)
        prompt = build_prompt("q", [chunk], [])
        assert "Operating Systems Lecture" in prompt

    def test_mp4_without_video_title_is_labeled_video_not_youtube(self):
        chunk = self._youtube_chunk("content", start=30.0)  # no video_title -> MP4-like
        prompt = build_prompt("q", [chunk], [])
        assert "Video" in prompt
        assert "YouTube" not in prompt

    def test_pdf_context_includes_page_provenance(self):
        chunk = self._pdf_chunk("Process scheduling text.", title="os.pdf", page=12)
        prompt = build_prompt("q", [chunk], [])
        assert "Page 12" in prompt
        assert "os.pdf" in prompt
        assert "Process scheduling text." in prompt

    def test_pdf_context_without_page_number_omits_it_gracefully(self):
        chunk = self._pdf_chunk("content", title="os.pdf")
        prompt = build_prompt("q", [chunk], [])
        assert "Document" in prompt
        assert "Page" not in prompt

    def test_missing_metadata_does_not_crash_prompt_construction(self):
        chunk = RetrievalResult(chunk_id="c1", text="bare content", relevance_score=0.9, metadata={})
        prompt = build_prompt("q", [chunk], [])
        assert "bare content" in prompt
        assert "[Context 1]" in prompt  # falls back to the pre-existing unlabeled format

    def test_unknown_source_type_falls_back_to_unlabeled_format(self):
        chunk = RetrievalResult(chunk_id="c1", text="content", relevance_score=0.9, metadata={"source_type": "weird"})
        prompt = build_prompt("q", [chunk], [])
        assert "[Context 1]" in prompt

    def test_multiple_contexts_each_get_their_own_correct_label(self):
        yt_chunk = self._youtube_chunk("video content", video_title="OS Lecture", start=60.0)
        pdf_chunk = self._pdf_chunk("pdf content", page=5)
        prompt = build_prompt("q", [yt_chunk, pdf_chunk], [])
        assert "[Context 1 \u2014 YouTube \u2014 OS Lecture \u2014 1:00]" in prompt
        assert "[Context 2 \u2014 Document \u2014 Page 5]" in prompt

    def test_existing_conversation_history_remains_intact(self):
        history = [_turn("user", "earlier question"), _turn("assistant", "earlier answer")]
        chunk = self._youtube_chunk("content", start=10.0)
        prompt = build_prompt("q", [chunk], history)
        assert "earlier question" in prompt
        assert "earlier answer" in prompt
        assert "=== Conversation History ===" in prompt

    def test_existing_system_instructions_remain_intact(self):
        prompt = build_prompt("q", [], [])
        assert "ONLY the information" in prompt
        assert "Do not invent, fabricate, or guess at citations" in prompt

    def test_no_retrieved_context_still_produces_the_existing_fallback_text(self):
        prompt = build_prompt("q", [], [])
        assert "(no retrieved context supplied)" in prompt

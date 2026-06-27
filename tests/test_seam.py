"""Tests for the OCR seam, concurrency resolution, and CLI."""

import base64
import io
from pathlib import Path

import pytest
from helpers import (
    _fake_image,
)
from PIL import Image


class TestOcrSeam:
    """The model seam is now an HTTP client to the vLLM server, so it is
    unit-testable with a mock transport — no GPU, no model load."""

    def test_ocr_page_request_shape_and_parsing(self) -> None:
        import json

        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        captured: dict[str, object] = {}

        def handler(request: httpx.Request) -> httpx.Response:
            captured["url"] = str(request.url)
            captured["body"] = json.loads(request.content)
            return httpx.Response(
                200, json={"choices": [{"message": {"content": "# OCR markdown"}}]}
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        result = _ocr_page(_fake_image(8, 8), ocr)

        assert result == "# OCR markdown"
        assert captured["url"] == "http://srv/v1/chat/completions"
        body = captured["body"]
        assert isinstance(body, dict)
        # Greedy decode (matches the former in-process do_sample=False) against
        # the served model name.
        assert body["temperature"] == 0.0
        assert body["model"] == "lightonocr"
        part = body["messages"][0]["content"][0]
        assert part["type"] == "image_url"
        assert part["image_url"]["url"].startswith("data:image/png;base64,")

    def test_ocr_page_raises_on_server_error(self) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        def handler(request: httpx.Request) -> httpx.Response:
            return httpx.Response(500, json={"error": "boom"})

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        with pytest.raises(httpx.HTTPStatusError):
            _ocr_page(_fake_image(8, 8), ocr)

    def test_ocr_page_null_content_returns_empty_string(self) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        def handler(request: httpx.Request) -> httpx.Response:
            body = {"choices": [{"message": {"content": None}}]}
            return httpx.Response(200, json=body)

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        # A degenerate page must yield "" (a str), not trip the return contract.
        assert _ocr_page(_fake_image(8, 8), ocr) == ""

    def test_ocr_page_raises_on_malformed_response(self) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        def handler(request: httpx.Request) -> httpx.Response:
            return httpx.Response(200, json={"choices": []})

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        with pytest.raises(RuntimeError, match="unexpected OCR response"):
            _ocr_page(_fake_image(8, 8), ocr)

    def test_ocr_page_null_choices_raises_runtime_error(self) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        # "choices": null is a null-valued key (None[0] -> TypeError), not a missing
        # one; it must still surface as the clear "unexpected OCR response" error.
        def handler(request: httpx.Request) -> httpx.Response:
            return httpx.Response(200, json={"choices": None})

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        with pytest.raises(RuntimeError, match="unexpected OCR response"):
            _ocr_page(_fake_image(8, 8), ocr)

    def test_ocr_page_non_string_content_raises(self) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        # Structured (non-null, non-string) content — e.g. OpenAI content parts —
        # is a response the pipeline can't consume; fail loudly rather than silently
        # transcribe the page as empty.
        def handler(request: httpx.Request) -> httpx.Response:
            body = {"choices": [{"message": {"content": [{"text": "x"}]}}]}
            return httpx.Response(200, json=body)

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        with pytest.raises(RuntimeError, match="unexpected OCR content type"):
            _ocr_page(_fake_image(8, 8), ocr)

    def test_truncated_page_is_reocrd_with_full_context(self) -> None:
        import json

        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        # First response truncates (finish_reason "length"); the seam must retry once
        # with the whole remaining context window (max-model-len 8192 − prompt − a
        # small margin) so the page's dropped tail is recovered.
        calls: list[int] = []
        truncated = "<table>the page up to the"
        # The full re-OCR reproduces the prefix and continues, so it is longer than
        # the truncated first response.
        full = truncated + " cut and the rest</table>"

        def handler(request: httpx.Request) -> httpx.Response:
            body = json.loads(request.content)
            calls.append(body["max_tokens"])
            content, reason = (
                (truncated, "length") if len(calls) == 1 else (full, "stop")
            )
            return httpx.Response(
                200,
                json={
                    "choices": [
                        {"message": {"content": content}, "finish_reason": reason}
                    ],
                    "usage": {"prompt_tokens": 2500},
                },
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        assert _ocr_page(_fake_image(8, 8), ocr) == full
        assert len(calls) == 2
        assert calls[0] == 2048
        # The retry claims the full remaining window, not just another fixed block.
        assert calls[1] == 8192 - 2500 - 64

    def test_natural_finish_does_not_retry(self) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        calls: list[int] = []

        def handler(request: httpx.Request) -> httpx.Response:
            calls.append(1)
            return httpx.Response(
                200,
                json={
                    "choices": [
                        {"message": {"content": "done"}, "finish_reason": "stop"}
                    ],
                    "usage": {"prompt_tokens": 2500},
                },
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        assert _ocr_page(_fake_image(8, 8), ocr) == "done"
        assert len(calls) == 1

    def test_truncation_without_headroom_keeps_best_effort(self) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        # The prompt already fills the window, so a retry has no more room than the
        # first call — keep the truncated text rather than re-OCRing for nothing.
        calls: list[int] = []

        def handler(request: httpx.Request) -> httpx.Response:
            calls.append(1)
            return httpx.Response(
                200,
                json={
                    "choices": [
                        {"message": {"content": "partial"}, "finish_reason": "length"}
                    ],
                    "usage": {"prompt_tokens": 8000},
                },
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        assert _ocr_page(_fake_image(8, 8), ocr) == "partial"
        assert len(calls) == 1

    def test_degenerate_retry_keeps_first_truncated_content(self) -> None:
        import json

        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        # First call truncates with usable text; the retry comes back degenerate
        # (null content -> ""). The good-but-truncated first response must be kept,
        # not replaced by the empty retry — otherwise the whole page is dropped.
        contents = ["a real but truncated page of markdown", None]

        def handler(request: httpx.Request) -> httpx.Response:
            json.loads(request.content)
            content = contents.pop(0)
            return httpx.Response(
                200,
                json={
                    "choices": [
                        {"message": {"content": content}, "finish_reason": "length"}
                    ],
                    "usage": {"prompt_tokens": 2500},
                },
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        assert (
            _ocr_page(_fake_image(8, 8), ocr) == "a real but truncated page of markdown"
        )

    def test_ocr_pages_preserves_order_under_concurrency(self) -> None:
        import json

        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_pages

        # Each page carries a distinct width so the handler can echo its identity;
        # concurrent completion must still gather back in input (page) order.
        def handler(request: httpx.Request) -> httpx.Response:
            body = json.loads(request.content)
            url = body["messages"][0]["content"][0]["image_url"]["url"]
            png = base64.b64decode(url.split(",", 1)[1])
            width = Image.open(io.BytesIO(png)).size[0]
            return httpx.Response(
                200, json={"choices": [{"message": {"content": f"page-{width}"}}]}
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        images = [_fake_image(w, 8) for w in range(10, 18)]
        result = _ocr_pages(images, ocr, concurrency=4)

        assert result == [f"page-{w}" for w in range(10, 18)]

    def test_ocr_pages_empty_input_returns_empty(self) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_pages

        # No images → no requests, no thread pool; returns [] without touching the
        # client (a handler that would fail the test if called).
        def handler(request: httpx.Request) -> httpx.Response:  # pragma: no cover
            raise AssertionError("no request should be issued for empty input")

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        assert _ocr_pages([], ocr) == []

    def test_ocr_pages_propagates_page_error(self) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_pages

        def handler(request: httpx.Request) -> httpx.Response:
            return httpx.Response(500, json={"error": "boom"})

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="lightonocr")
        with pytest.raises(httpx.HTTPStatusError):
            _ocr_pages([_fake_image(8, 8), _fake_image(9, 8)], ocr, concurrency=2)

    def test_ocr_model_context_manager_closes_client(self) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel

        transport = httpx.MockTransport(lambda r: httpx.Response(200))
        client = httpx.Client(transport=transport)
        with OcrModel(client=client, base_url="http://srv/v1", model="m") as ocr:
            assert not ocr.client.is_closed
        assert client.is_closed

    @staticmethod
    def _patch_client(monkeypatch: pytest.MonkeyPatch, handler: object) -> list[object]:
        """Make ``model.load_ocr_model``'s internal ``httpx.Client(...)`` use a mock
        transport; return the list of clients it builds so a test can assert on the
        pool's lifecycle."""
        import httpx

        from pdfparser.pipeline import model

        built: list[object] = []
        real_client = httpx.Client

        def fake_client(**kwargs: object) -> httpx.Client:
            client = real_client(transport=httpx.MockTransport(handler), **kwargs)
            built.append(client)
            return client

        monkeypatch.setattr(model.httpx, "Client", fake_client)
        return built

    def test_load_ocr_model_probes_models_and_strips_trailing_slash(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline.model import load_ocr_model

        seen: dict[str, str] = {}

        def handler(request: httpx.Request) -> httpx.Response:
            seen["url"] = str(request.url)
            return httpx.Response(200, json={"data": []})

        self._patch_client(monkeypatch, handler)
        ocr = load_ocr_model(base_url="http://srv/v1/", model="m")
        # the trailing slash is stripped and the reachability probe hits /models
        assert seen["url"] == "http://srv/v1/models"
        assert ocr.base_url == "http://srv/v1"
        assert ocr.model == "m"
        ocr.close()

    def test_load_ocr_model_reads_env_defaults(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline.model import load_ocr_model

        monkeypatch.setenv("PDFPARSER_VLLM_URL", "http://envhost:9/v1")
        monkeypatch.setenv("PDFPARSER_VLLM_MODEL", "envmodel")
        seen: dict[str, str] = {}

        def handler(request: httpx.Request) -> httpx.Response:
            seen["url"] = str(request.url)
            return httpx.Response(200)

        self._patch_client(monkeypatch, handler)
        ocr = load_ocr_model()
        assert seen["url"] == "http://envhost:9/v1/models"
        assert ocr.model == "envmodel"
        ocr.close()

    def test_load_ocr_model_stores_resolved_concurrency(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline import model
        from pdfparser.pipeline.model import load_ocr_model

        # Concurrency is resolved once at load and stored on the model *and* used to
        # size the httpx pool, so the pool cap and the _ocr_pages worker count can't
        # desync (a late env change is then ignored by both).
        monkeypatch.setenv("PDFPARSER_OCR_CONCURRENCY", "6")
        captured: dict[str, httpx.Limits] = {}
        real_client = httpx.Client

        def fake_client(**kwargs: object) -> httpx.Client:
            captured["limits"] = kwargs["limits"]  # type: ignore[assignment]
            return real_client(
                transport=httpx.MockTransport(
                    lambda request: httpx.Response(200, json={"data": []})
                ),
                **kwargs,
            )

        monkeypatch.setattr(model.httpx, "Client", fake_client)
        ocr = load_ocr_model(base_url="http://srv/v1", model="m")
        assert ocr.concurrency == 6
        assert captured["limits"].max_connections == 6
        ocr.close()

    def test_load_ocr_model_closes_client_when_probe_fails(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline.model import load_ocr_model

        built = self._patch_client(
            monkeypatch, lambda request: httpx.Response(503, json={"error": "down"})
        )
        with pytest.raises(httpx.HTTPStatusError):
            load_ocr_model(base_url="http://srv/v1")
        # the probe failed, so the pool must be torn down rather than leaked
        assert built and built[0].is_closed  # type: ignore[attr-defined]


class TestOcrTransientRetry:
    """A transient connection blip or vLLM overload status on one page must not
    abort the whole document — it is retried with backoff; a non-retryable status
    and an exhausted retry still propagate."""

    @staticmethod
    def _record_sleeps(monkeypatch: pytest.MonkeyPatch) -> list[float]:
        """Stub out the backoff sleep and return the list it records each delay into."""
        from pdfparser.pipeline import model

        delays: list[float] = []
        monkeypatch.setattr(model.time, "sleep", lambda s: delays.append(s))
        return delays

    @staticmethod
    def _no_sleep(monkeypatch: pytest.MonkeyPatch) -> None:
        from pdfparser.pipeline import model

        monkeypatch.setattr(model.time, "sleep", lambda _s: None)

    def test_retryable_status_then_success(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        self._no_sleep(monkeypatch)
        calls: list[int] = []

        def handler(request: httpx.Request) -> httpx.Response:
            calls.append(1)
            if len(calls) < 3:  # two transient 503s, then a good response
                return httpx.Response(503, json={"error": "overloaded"})
            return httpx.Response(
                200, json={"choices": [{"message": {"content": "recovered"}}]}
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="m")
        assert _ocr_page(_fake_image(8, 8), ocr) == "recovered"
        assert len(calls) == 3

    def test_transport_error_then_success(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        self._no_sleep(monkeypatch)
        calls: list[int] = []

        def handler(request: httpx.Request) -> httpx.Response:
            calls.append(1)
            if len(calls) == 1:
                raise httpx.ConnectError("connection reset")
            return httpx.Response(
                200, json={"choices": [{"message": {"content": "ok"}}]}
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="m")
        assert _ocr_page(_fake_image(8, 8), ocr) == "ok"
        assert len(calls) == 2

    def test_remote_protocol_error_then_success(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        self._no_sleep(monkeypatch)
        calls: list[int] = []

        # A peer disconnect mid-response (RemoteProtocolError) is the canonical
        # transient on a busy shared vLLM; it is a *sibling* of NetworkError under
        # TransportError, not a subclass, so it must be retried explicitly rather than
        # fall through to the re-raise.
        def handler(request: httpx.Request) -> httpx.Response:
            calls.append(1)
            if len(calls) == 1:
                raise httpx.RemoteProtocolError(
                    "server disconnected without sending a complete response"
                )
            return httpx.Response(
                200, json={"choices": [{"message": {"content": "ok"}}]}
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="m")
        assert _ocr_page(_fake_image(8, 8), ocr) == "ok"
        assert len(calls) == 2

    def test_backoff_has_jitter(self, monkeypatch: pytest.MonkeyPatch) -> None:
        import httpx

        from pdfparser.pipeline import model
        from pdfparser.pipeline.model import _RETRY_BACKOFF_BASE_S, OcrModel, _ocr_page

        delays = self._record_sleeps(monkeypatch)
        # Pin the jitter term so the exact sleep is assertable; the point under test is
        # that it is *added* to the deterministic exponential backoff, so several pages
        # retrying in lockstep don't stampede the just-overloaded server in sync.
        monkeypatch.setattr(model.random, "uniform", lambda _a, _b: 0.123)
        calls: list[int] = []

        # A 503 with no Retry-After header takes the backoff branch (not the honored
        # Retry-After path, which stays jitter-free).
        def handler(request: httpx.Request) -> httpx.Response:
            calls.append(1)
            if len(calls) == 1:
                return httpx.Response(503, json={"error": "overloaded"})
            return httpx.Response(
                200, json={"choices": [{"message": {"content": "ok"}}]}
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="m")
        assert _ocr_page(_fake_image(8, 8), ocr) == "ok"
        # attempt-0 backoff (base * 2**0) plus the pinned jitter term
        assert delays == [_RETRY_BACKOFF_BASE_S + 0.123]

    def test_retries_exhausted_reraises(self, monkeypatch: pytest.MonkeyPatch) -> None:
        import httpx

        from pdfparser.pipeline.model import _MAX_OCR_RETRIES, OcrModel, _ocr_page

        self._no_sleep(monkeypatch)
        calls: list[int] = []

        def handler(request: httpx.Request) -> httpx.Response:
            calls.append(1)
            return httpx.Response(503, json={"error": "down"})

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="m")
        with pytest.raises(httpx.HTTPStatusError):
            _ocr_page(_fake_image(8, 8), ocr)
        # the initial attempt plus exactly _MAX_OCR_RETRIES retries, then it gives up
        assert len(calls) == _MAX_OCR_RETRIES + 1

    def test_non_retryable_status_not_retried(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        self._no_sleep(monkeypatch)
        calls: list[int] = []

        # A 400 is a caller bug, not a transient blip — retrying re-fails identically,
        # so it must propagate on the first attempt.
        def handler(request: httpx.Request) -> httpx.Response:
            calls.append(1)
            return httpx.Response(400, json={"error": "bad request"})

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="m")
        with pytest.raises(httpx.HTTPStatusError):
            _ocr_page(_fake_image(8, 8), ocr)
        assert len(calls) == 1

    def test_read_timeout_is_not_retried(self, monkeypatch: pytest.MonkeyPatch) -> None:
        import httpx

        from pdfparser.pipeline.model import OcrModel, _ocr_page

        self._no_sleep(monkeypatch)
        calls: list[int] = []

        # A read timeout already spent the full per-request budget; retrying would
        # re-spend it (~3× the 600s timeout) and defeats _ocr_pages' fast-fail of a
        # wedged page — so it must propagate on the first attempt, unlike a connection
        # blip (ConnectError, a NetworkError) which IS retried.
        def handler(request: httpx.Request) -> httpx.Response:
            calls.append(1)
            raise httpx.ReadTimeout("read timed out")

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="m")
        with pytest.raises(httpx.ReadTimeout):
            _ocr_page(_fake_image(8, 8), ocr)
        assert len(calls) == 1

    def test_retry_after_header_is_honored_and_capped(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline.model import _MAX_RETRY_AFTER_S, OcrModel, _ocr_page

        delays = self._record_sleeps(monkeypatch)
        calls: list[int] = []
        # First a 503 with a sane Retry-After (honored verbatim), then a 503 with an
        # absurd one (capped), then success — the client waits the server's hint rather
        # than piling load back onto a busy server.
        retry_afters = ["2", "9999"]

        def handler(request: httpx.Request) -> httpx.Response:
            calls.append(1)
            if retry_afters:
                return httpx.Response(503, headers={"Retry-After": retry_afters.pop(0)})
            return httpx.Response(
                200, json={"choices": [{"message": {"content": "ok"}}]}
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(client=client, base_url="http://srv/v1", model="m")
        assert _ocr_page(_fake_image(8, 8), ocr) == "ok"
        assert delays == [2.0, _MAX_RETRY_AFTER_S]


class TestOcrConcurrencyResolution:
    """``PDFPARSER_OCR_CONCURRENCY`` parsing — defaulting, flooring, and the
    misconfiguration warning — without spinning up the thread pool."""

    def test_default_when_unset(self, monkeypatch: pytest.MonkeyPatch) -> None:
        from pdfparser.pipeline.model import (
            _DEFAULT_OCR_CONCURRENCY,
            _resolve_ocr_concurrency,
        )

        monkeypatch.delenv("PDFPARSER_OCR_CONCURRENCY", raising=False)
        assert _resolve_ocr_concurrency() == _DEFAULT_OCR_CONCURRENCY

    def test_valid_integer_is_honored(self, monkeypatch: pytest.MonkeyPatch) -> None:
        from pdfparser.pipeline.model import _resolve_ocr_concurrency

        monkeypatch.setenv("PDFPARSER_OCR_CONCURRENCY", "7")
        assert _resolve_ocr_concurrency() == 7

    def test_floored_at_one(self, monkeypatch: pytest.MonkeyPatch) -> None:
        from pdfparser.pipeline.model import _resolve_ocr_concurrency

        monkeypatch.setenv("PDFPARSER_OCR_CONCURRENCY", "0")
        assert _resolve_ocr_concurrency() == 1

    def test_non_integer_warns_and_falls_back(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        from pdfparser.pipeline.model import (
            _DEFAULT_OCR_CONCURRENCY,
            _resolve_ocr_concurrency,
        )

        monkeypatch.setenv("PDFPARSER_OCR_CONCURRENCY", "lots")
        # a misconfigured deployment is surfaced, not silently defaulted
        with pytest.warns(UserWarning, match="not an integer"):
            assert _resolve_ocr_concurrency() == _DEFAULT_OCR_CONCURRENCY

    def test_ocr_pages_uses_model_concurrency_not_env(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        from concurrent.futures import ThreadPoolExecutor

        import httpx

        from pdfparser.pipeline import model
        from pdfparser.pipeline.model import OcrModel, _ocr_pages

        # Env raised *after* load must not change the worker count: it is taken from the
        # value resolved at load time (OcrModel.concurrency), which also sized the httpx
        # pool — so a late env change can't desync the workers from the pool cap.
        monkeypatch.setenv("PDFPARSER_OCR_CONCURRENCY", "9")
        captured: list[int] = []
        real_pool = model.ThreadPoolExecutor

        def spy_pool(max_workers: int) -> ThreadPoolExecutor:
            captured.append(max_workers)
            return real_pool(max_workers=max_workers)

        monkeypatch.setattr(model, "ThreadPoolExecutor", spy_pool)

        def handler(request: httpx.Request) -> httpx.Response:
            return httpx.Response(
                200, json={"choices": [{"message": {"content": "ok"}}]}
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(
            client=client, base_url="http://srv/v1", model="m", concurrency=3
        )
        images = [_fake_image(8, 8) for _ in range(5)]
        assert _ocr_pages(images, ocr) == ["ok"] * 5
        # worker count is ocr.concurrency (3), floored by the image count — not the
        # post-load env value (9)
        assert captured == [3]


class TestCli:
    """The ``python -m pdfparser`` entry point: output-path defaulting and option
    forwarding, with the conversion itself stubbed (no model, no rendering)."""

    @staticmethod
    def _make_pdf(tmp_path: Path) -> Path:
        pdf = tmp_path / "paper.pdf"
        pdf.write_bytes(b"%PDF-1.4")
        return pdf

    def test_default_output_path_derived_from_pdf_suffix(
        self, tmp_path: Path, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import pdfparser.__main__ as cli

        pdf = self._make_pdf(tmp_path)
        captured: dict[str, object] = {}

        def fake_convert(p: Path, **kwargs: object) -> str:
            captured["pdf"] = p
            captured["kwargs"] = kwargs
            return "<html>ok</html>"

        monkeypatch.setattr(cli, "lightonocr_pdf_to_html", fake_convert)
        assert cli.main([str(pdf)]) == 0
        # default output is the input path with a .html suffix
        out = (tmp_path / "paper.html").read_text(encoding="utf-8")
        assert out == "<html>ok</html>"
        assert captured["pdf"] == pdf
        assert captured["kwargs"] == {
            "base_url": None,
            "model": None,
            "image_dir": None,
        }

    def test_explicit_output_and_options_forwarded(
        self, tmp_path: Path, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import pdfparser.__main__ as cli

        pdf = self._make_pdf(tmp_path)
        out = tmp_path / "custom.html"
        image_dir = tmp_path / "imgs"
        captured: dict[str, object] = {}

        def fake_convert(p: Path, **kwargs: object) -> str:
            captured.update(kwargs)
            return "<html></html>"

        monkeypatch.setattr(cli, "lightonocr_pdf_to_html", fake_convert)
        rc = cli.main(
            [
                str(pdf),
                str(out),
                "--vllm-url",
                "http://h/v1",
                "--vllm-model",
                "m",
                "--image-dir",
                str(image_dir),
            ]
        )
        assert rc == 0
        assert out.read_text(encoding="utf-8") == "<html></html>"
        assert captured["base_url"] == "http://h/v1"
        assert captured["model"] == "m"
        assert captured["image_dir"] == image_dir

    def test_missing_pdf_errors_before_conversion(
        self, tmp_path: Path, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import pdfparser.__main__ as cli

        called: list[int] = []
        monkeypatch.setattr(
            cli,
            "lightonocr_pdf_to_html",
            lambda *a, **k: called.append(1) or "",
        )
        # argparse's parser.error exits with code 2 and the convert is never reached
        with pytest.raises(SystemExit) as exc:
            cli.main([str(tmp_path / "absent.pdf")])
        assert exc.value.code == 2
        assert not called

    def test_unreachable_server_prints_message_returns_1(
        self,
        tmp_path: Path,
        monkeypatch: pytest.MonkeyPatch,
        capsys: pytest.CaptureFixture[str],
    ) -> None:
        import httpx

        import pdfparser.__main__ as cli

        pdf = self._make_pdf(tmp_path)

        def boom(*a: object, **k: object) -> str:
            raise httpx.ConnectError("connection refused")

        monkeypatch.setattr(cli, "lightonocr_pdf_to_html", boom)
        # An unreachable server must yield a concise stderr message naming the resolved
        # base URL and a non-zero exit, not a raw traceback or a written output file.
        rc = cli.main([str(pdf), "--vllm-url", "http://down:9/v1"])
        assert rc == 1
        err = capsys.readouterr().err
        assert "http://down:9/v1" in err
        assert "connection refused" in err
        assert not (tmp_path / "paper.html").exists()


class TestServerContextWindow:
    """The server's ``max_model_len`` (the truncation-retry budget) is resolved once
    at load time from ``/models``, with the env var as override — not re-read from
    ``os.environ`` per page."""

    def test_parse_server_context_len_extracts_max_model_len(self) -> None:
        from pdfparser.pipeline.model import _parse_server_context_len

        payload = {"object": "list", "data": [{"id": "m", "max_model_len": 16384}]}
        assert _parse_server_context_len(payload) == 16384

    @pytest.mark.parametrize(
        "payload",
        [
            None,
            {},
            {"data": []},
            {"data": "nope"},
            {"data": [{"id": "m"}]},  # no max_model_len (older server)
            {"data": [{"id": "m", "max_model_len": 0}]},  # non-positive
            {"data": [{"id": "m", "max_model_len": "8192"}]},  # wrong type
        ],
    )
    def test_parse_server_context_len_none_on_missing_or_bad_shape(
        self, payload: object
    ) -> None:
        from pdfparser.pipeline.model import _parse_server_context_len

        assert _parse_server_context_len(payload) is None

    def test_resolve_prefers_reported_over_default(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        from pdfparser.pipeline.model import _resolve_context_len

        monkeypatch.delenv("PDFPARSER_VLLM_MAX_MODEL_LEN", raising=False)
        assert _resolve_context_len(16384) == 16384

    def test_resolve_falls_back_to_default_when_unreported(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        from pdfparser.pipeline.model import (
            _DEFAULT_MODEL_CONTEXT_LEN,
            _resolve_context_len,
        )

        monkeypatch.delenv("PDFPARSER_VLLM_MAX_MODEL_LEN", raising=False)
        assert _resolve_context_len(None) == _DEFAULT_MODEL_CONTEXT_LEN

    def test_env_override_beats_reported(self, monkeypatch: pytest.MonkeyPatch) -> None:
        from pdfparser.pipeline.model import _resolve_context_len

        monkeypatch.setenv("PDFPARSER_VLLM_MAX_MODEL_LEN", "5000")
        assert _resolve_context_len(16384) == 5000

    def test_bad_env_override_warns_and_falls_back_to_reported(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        from pdfparser.pipeline.model import _resolve_context_len

        monkeypatch.setenv("PDFPARSER_VLLM_MAX_MODEL_LEN", "lots")
        with pytest.warns(UserWarning):
            assert _resolve_context_len(16384) == 16384

    def test_load_ocr_model_stores_reported_window(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline.model import load_ocr_model

        monkeypatch.delenv("PDFPARSER_VLLM_MAX_MODEL_LEN", raising=False)

        def handler(request: httpx.Request) -> httpx.Response:
            return httpx.Response(200, json={"data": [{"max_model_len": 16384}]})

        TestOcrSeam._patch_client(monkeypatch, handler)
        ocr = load_ocr_model(base_url="http://srv/v1")
        assert ocr.context_len == 16384
        ocr.close()

    def test_load_ocr_model_env_override_beats_reported_window(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline.model import load_ocr_model

        monkeypatch.setenv("PDFPARSER_VLLM_MAX_MODEL_LEN", "4096")

        def handler(request: httpx.Request) -> httpx.Response:
            return httpx.Response(200, json={"data": [{"max_model_len": 16384}]})

        TestOcrSeam._patch_client(monkeypatch, handler)
        ocr = load_ocr_model(base_url="http://srv/v1")
        assert ocr.context_len == 4096
        ocr.close()

    def test_load_ocr_model_defaults_window_when_unreported(
        self, monkeypatch: pytest.MonkeyPatch
    ) -> None:
        import httpx

        from pdfparser.pipeline.model import (
            _DEFAULT_MODEL_CONTEXT_LEN,
            load_ocr_model,
        )

        monkeypatch.delenv("PDFPARSER_VLLM_MAX_MODEL_LEN", raising=False)

        # A bare-200 probe (no JSON body) must not crash resolution.
        def handler(request: httpx.Request) -> httpx.Response:
            return httpx.Response(200)

        TestOcrSeam._patch_client(monkeypatch, handler)
        ocr = load_ocr_model(base_url="http://srv/v1")
        assert ocr.context_len == _DEFAULT_MODEL_CONTEXT_LEN
        ocr.close()

    def test_ocr_page_retry_budget_uses_stored_window(self) -> None:
        import json

        import httpx

        from pdfparser.pipeline.model import _CONTEXT_SAFETY_MARGIN, OcrModel, _ocr_page

        # The truncation retry must size its max_tokens off the bundle's context_len,
        # not a hardcoded/env-read default — proving the per-page os.environ re-read is
        # gone and a non-default server window is honored.
        calls: list[int] = []
        truncated = "<table>cut"
        full = truncated + " and the rest</table>"

        def handler(request: httpx.Request) -> httpx.Response:
            body = json.loads(request.content)
            calls.append(body["max_tokens"])
            content, reason = (
                (truncated, "length") if len(calls) == 1 else (full, "stop")
            )
            return httpx.Response(
                200,
                json={
                    "choices": [
                        {"message": {"content": content}, "finish_reason": reason}
                    ],
                    "usage": {"prompt_tokens": 1000},
                },
            )

        client = httpx.Client(transport=httpx.MockTransport(handler))
        ocr = OcrModel(
            client=client, base_url="http://srv/v1", model="m", context_len=4096
        )
        assert _ocr_page(_fake_image(8, 8), ocr) == full
        assert calls[1] == 4096 - 1000 - _CONTEXT_SAFETY_MARGIN

    def test_client_limits_track_concurrency(self) -> None:
        from pdfparser.pipeline.model import _client_limits

        # the pool is sized to exactly the resolved worker count, both caps (the
        # env→worker-count resolution is exercised end-to-end by the load test below)
        limits = _client_limits(9)
        assert limits.max_connections == 9
        assert limits.max_keepalive_connections == 9

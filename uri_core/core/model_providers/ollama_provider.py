"""ModelProvider backed by a local or remote Ollama server's HTTP API.

Talks to Ollama's /api/chat endpoint directly - no shelling out to the
`ollama` executable. All connection details come from ModelProviderConfig
so nothing here is hardcoded beyond that config's own defaults.
"""

import json
import logging
import time
import uuid
from typing import Any, Dict, List, Optional

import requests

from uri_desktop_seams.ollama_residency import guard_completion
from uri_core.core.context_budget import estimate_tokens

from .base import (
    DEFAULT_CONTEXT_TOKENS,
    DEFAULT_HEALTH_CHECK_TIMEOUT_SECONDS,
    DEFAULT_OLLAMA_BASE_URL,
    DEFAULT_OLLAMA_MODEL,
    ContextWindowExceededError,
    ModelNotFoundError,
    ModelProvider,
    ModelProviderConfig,
    ModelProviderStatus,
    ModelResponse,
    ProviderResponseError,
    ProviderTimeoutError,
    ProviderUnavailableError,
    StreamChunk,
    ToolCall,
    _location_from_base_url,
)

# M21: plain numeric instrumentation only (prompt/eval token counts,
# duration, configured window) - never raw prompt/response content, matching
# ModelResponse's own "no raw backend payload" discipline. This is what lets
# a real truncation (prompt_eval_count far below the true prompt size) show
# up in ordinary logs instead of silently degrading the model's answer with
# no visible signal anywhere - see the M21 audit's core finding.
_LOG = logging.getLogger(__name__)


def probe_model_max_context(
    base_url: str = DEFAULT_OLLAMA_BASE_URL,
    model: str = DEFAULT_OLLAMA_MODEL,
    timeout_seconds: float = DEFAULT_HEALTH_CHECK_TIMEOUT_SECONDS,
) -> Optional[int]:
    """Probes Ollama's /api/tags for the model's supported context_length.
    Returns None on any network error, timeout, or missing field.
    Never raises."""
    try:
        url = f"{base_url.rstrip('/')}/api/tags"
        response = requests.get(url, timeout=timeout_seconds)
        if response.status_code != 200:
            return None
        body = response.json()
        if not isinstance(body, dict):
            return None
        for entry in body.get("models", []):
            if not isinstance(entry, dict):
                continue
            entry_name = entry.get("name", "")
            if (
                entry_name == model
                or entry_name == f"{model}:latest"
                or (model.endswith(":latest") and entry_name == model[:-7])
            ):
                details = entry.get("details")
                if isinstance(details, dict):
                    val = details.get("context_length")
                    if isinstance(val, int) and val > 0:
                        return val
    except Exception:
        return None
    return None


def resolve_model_context_tokens(
    model: str = DEFAULT_OLLAMA_MODEL,
    base_url: str = DEFAULT_OLLAMA_BASE_URL,
    default: int = DEFAULT_CONTEXT_TOKENS,
) -> int:
    """Resolves the context window for an Ollama model in strict priority order:
    1. Explicit OLLAMA_NUM_CTX environment variable override
    2. Live discovery from Ollama /api/tags (probe_model_max_context)
    3. Known value from provider catalogue (provider_registry)
    4. Conservative default fallback (DEFAULT_CONTEXT_TOKENS = 8192)
    """
    import os

    if "OLLAMA_NUM_CTX" in os.environ:
        try:
            return int(os.environ["OLLAMA_NUM_CTX"])
        except ValueError:
            pass

    discovered = probe_model_max_context(base_url=base_url, model=model)
    if isinstance(discovered, int) and discovered > 0:
        return discovered

    from uri_core.core.provider_registry import get_catalogue_context_tokens

    catalogue_val = get_catalogue_context_tokens(model, provider_id="ollama")
    if isinstance(catalogue_val, int) and catalogue_val > 0:
        return catalogue_val

    return default


def _parse_ollama_tool_calls(raw_tool_calls: Any) -> tuple:
    """Normalises Ollama's raw ``message.tool_calls`` list (dict entries
    with a nested ``"function": {"name", "arguments"}``) into a tuple of
    ``ToolCall``. Shared by ``complete()`` and ``complete_stream()`` (M32
    D5) so the two can never independently drift on this parsing.
    Returns an empty tuple for anything not shaped as a list."""
    if not isinstance(raw_tool_calls, list):
        return ()
    collected = []
    for entry in raw_tool_calls:
        if not isinstance(entry, dict):
            continue
        function = entry.get("function")
        if not isinstance(function, dict):
            continue
        name = function.get("name")
        if not isinstance(name, str) or not name:
            continue
        arguments = function.get("arguments")
        if not isinstance(arguments, dict):
            arguments = {}
        collected.append(
            ToolCall(
                id=str(entry.get("id") or uuid.uuid4()),
                name=name,
                arguments=arguments,
            )
        )
    return tuple(collected)


class OllamaProvider(ModelProvider):
    def __init__(self, config: Optional[ModelProviderConfig] = None):
        self.config = config or ModelProviderConfig.from_env()

    def _build_chat_payload(
        self,
        *,
        system: str,
        user: str,
        temperature: float,
        max_tokens: Optional[int],
        tools: Optional[List[Dict[str, Any]]],
        stream: bool,
    ) -> Dict[str, Any]:
        """Shared request-payload construction for both ``complete()``
        and ``complete_stream()`` (M32 D5) - identical in every field
        except ``stream``, so the two can never independently drift."""
        payload = {
            "model": self.config.model,
            "messages": [
                {"role": "system", "content": system},
                {"role": "user", "content": user},
            ],
            "stream": stream,
            # 2026-09-12 (User directive): without this, Ollama evicts an
            # idle model from memory on its own short default timeout,
            # so the next turn pays a real 10-20s reload cost before any
            # inference even starts. URI issues several sequential calls
            # per turn (semantic analysis, reasoning, drafting) and turns
            # are rarely more than a few minutes apart in a live
            # conversation, so keeping the model resident for 60 minutes
            # of idle time removes that reload cost from every turn but
            # the very first of a session.
            "keep_alive": "60m",
            # Thinking-capable models (e.g. qwen3) generate a chain-of-
            # thought trace *before* the visible content, and that trace
            # is counted against max_tokens/num_predict - so a token
            # budget sized for the answer alone can truncate the answer
            # itself before it's written. URI's current callers all want
            # a short, deterministic, structured completion, not a
            # visible reasoning trace, so thinking is switched off here.
            # Ollama ignores this field for models that don't support it.
            "think": False,
            "options": {
                "temperature": temperature,
                # M21: previously unset, which left Ollama loading the
                # model at its own hardcoded 4096-token default regardless
                # of how large a prompt this call actually sent - measured
                # during the M21 audit to silently discard the majority of
                # every real Brain prompt (a 4935-token reasoning request
                # was evaluated as 2050 tokens, destroying the leading
                # system_policy/contract text first). Always explicit now.
                "num_ctx": self.config.context_tokens,
            },
        }

        if max_tokens is not None:
            payload["options"]["num_predict"] = max_tokens

        # M32 C1: Ollama's /api/chat accepts the same OpenAI-compatible
        # `tools` array the caller already builds (tool_schema.py) - passed
        # through verbatim, additive, and a no-op (Ollama simply never
        # populates message.tool_calls) for a model with no tool-calling
        # support. estimate_tokens below intentionally does not count
        # `tools` - the context-budget module trims/reserves headroom for
        # the tool catalogue itself (see context_trimmer.py's own
        # available_capabilities cap), not this adapter.
        if tools:
            payload["tools"] = tools

        return payload

    def _check_context_window(
        self, *, system: str, user: str, max_tokens: Optional[int]
    ) -> None:
        """Shared pre-flight context-window guard for both ``complete()``
        and ``complete_stream()`` - raises ``ContextWindowExceededError``
        identically for either, never silently truncating a prompt."""
        estimated_prompt_tokens = estimate_tokens(system) + estimate_tokens(user)
        headroom = max_tokens or 0
        total_required_tokens = estimated_prompt_tokens + headroom

        if total_required_tokens > self.config.context_tokens:
            msg = (
                f"Prompt estimated at ~{estimated_prompt_tokens} tokens with {headroom} token output "
                f"headroom ({total_required_tokens} total) exceeds configured context window "
                f"({self.config.context_tokens} tokens) for model '{self.config.model}'. "
                "Refusing execution to protect system policy and identity integrity."
            )
            _LOG.error(msg)
            raise ContextWindowExceededError(
                msg,
                model=self.config.model,
                prompt_tokens=estimated_prompt_tokens,
                max_tokens=headroom,
                context_tokens=self.config.context_tokens,
            )

    @guard_completion
    def complete(
        self,
        *,
        system: str,
        user: str,
        temperature: float = 0.0,
        max_tokens: Optional[int] = None,
        tools: Optional[List[Dict[str, Any]]] = None,
    ) -> ModelResponse:

        payload = self._build_chat_payload(
            system=system, user=user, temperature=temperature,
            max_tokens=max_tokens, tools=tools, stream=False,
        )
        self._check_context_window(system=system, user=user, max_tokens=max_tokens)

        url = f"{self.config.base_url.rstrip('/')}/api/chat"

        start = time.monotonic()

        try:
            response = requests.post(
                url,
                json=payload,
                timeout=self.config.timeout_seconds,
            )
        except requests.exceptions.Timeout as exc:
            raise ProviderTimeoutError(
                f"Ollama did not respond within {self.config.timeout_seconds}s."
            ) from exc
        except requests.exceptions.ConnectionError as exc:
            raise ProviderUnavailableError(
                f"Could not reach Ollama at {self.config.base_url}. "
                "Is it running?"
            ) from exc
        except requests.exceptions.RequestException as exc:
            raise ProviderUnavailableError(
                f"Request to Ollama failed: {exc}"
            ) from exc

        if response.status_code == 404:
            raise ModelNotFoundError(
                f"Model '{self.config.model}' was not found on this Ollama "
                f"server ({self.config.base_url}). Pull it first."
            )

        if response.status_code != 200:
            raise ProviderResponseError(
                f"Ollama returned HTTP {response.status_code}: "
                f"{response.text[:200]}"
            )

        try:
            data = response.json()
        except ValueError as exc:
            raise ProviderResponseError(
                "Ollama returned a response that was not valid JSON."
            ) from exc

        message = data.get("message")

        if not isinstance(message, dict) or not isinstance(
            message.get("content"), str
        ):
            raise ProviderResponseError(
                "Ollama response did not contain message.content."
            )

        duration_seconds = time.monotonic() - start
        prompt_tokens = data.get("prompt_eval_count")
        eval_tokens = data.get("eval_count")

        # M32 C1: Ollama's own tool_calls shape is already
        # [{"function": {"name": str, "arguments": dict}}, ...] - dict
        # arguments, not a JSON string (unlike OpenAI's wire format) - no
        # extra parsing needed. Ollama does not supply a per-call id, so
        # one is generated here so every ToolCall always has a real,
        # non-empty id a continuation message can reference.
        raw_tool_calls = message.get("tool_calls")
        parsed_tool_calls: Optional[tuple] = (
            _parse_ollama_tool_calls(raw_tool_calls) if tools else None
        )

        if isinstance(prompt_tokens, int):
            _LOG.info(
                "Ollama completion: model=%s prompt_tokens=%d eval_tokens=%s "
                "duration=%.2fs num_ctx=%d",
                self.config.model,
                prompt_tokens,
                eval_tokens,
                duration_seconds,
                self.config.context_tokens,
            )
            estimated_prompt_tokens = estimate_tokens(system) + estimate_tokens(user)
            if prompt_tokens < estimated_prompt_tokens * 0.7:
                _LOG.warning(
                    "Ollama reported prompt_tokens=%d for a prompt "
                    "estimated at ~%d tokens - the request may have been "
                    "truncated to fit context_tokens=%d.",
                    prompt_tokens,
                    estimated_prompt_tokens,
                    self.config.context_tokens,
                )

        return ModelResponse(
            content=message["content"],
            model=data.get("model", self.config.model),
            provider="ollama",
            prompt_tokens=prompt_tokens if isinstance(prompt_tokens, int) else None,
            eval_tokens=eval_tokens if isinstance(eval_tokens, int) else None,
            duration_seconds=duration_seconds,
            tool_calls=parsed_tool_calls,
        )

    @guard_completion
    def complete_stream(
        self,
        *,
        system: str,
        user: str,
        temperature: float = 0.0,
        max_tokens: Optional[int] = None,
        tools: Optional[List[Dict[str, Any]]] = None,
    ):
        """M32 D5: real token-by-token streaming, against Ollama's own
        `/api/chat` with `"stream": true` - real NDJSON lines, one
        `{"message": {"content": <delta>[, "tool_calls": [...]]}, "done":
        bool, ...}` object per line, confirmed live against this
        deployment's own Ollama server before this was written (see
        M32_POST_BATCH_C_LATENCY_ARCHITECTURE_PLAN.md §13/§14).

        Live-confirmed tool-calling behaviour this depends on: when the
        model calls a tool, Ollama's FIRST streamed line already carries
        the full `message.tool_calls` array with `content: ""` - no
        prose precedes it. This still yields every chunk (content or
        tool-call) as it arrives rather than assuming that ordering
        internally; a caller must still treat `is_tool_call=True` on
        ANY chunk (not just the first) as reason to discard every prior
        `content` delta as provisional (see `StreamChunk`'s own
        docstring) - this method never makes that judgement call itself.

        Yields one `StreamChunk` per NDJSON line, plus a final
        `done=True` chunk carrying the complete, real `ModelResponse` -
        constructed identically in shape to what `complete()` returns
        for the same request, so a caller already written against
        `complete()`'s result can consume `final_response` unchanged.
        """
        payload = self._build_chat_payload(
            system=system, user=user, temperature=temperature,
            max_tokens=max_tokens, tools=tools, stream=True,
        )
        self._check_context_window(system=system, user=user, max_tokens=max_tokens)

        url = f"{self.config.base_url.rstrip('/')}/api/chat"
        start = time.monotonic()
        ttft: Optional[float] = None
        accumulated_content: List[str] = []
        tool_calls_final: Optional[tuple] = None

        try:
            response = requests.post(
                url, json=payload, timeout=self.config.timeout_seconds, stream=True,
            )
        except requests.exceptions.Timeout as exc:
            raise ProviderTimeoutError(
                f"Ollama did not respond within {self.config.timeout_seconds}s."
            ) from exc
        except requests.exceptions.ConnectionError as exc:
            raise ProviderUnavailableError(
                f"Could not reach Ollama at {self.config.base_url}. "
                "Is it running?"
            ) from exc
        except requests.exceptions.RequestException as exc:
            raise ProviderUnavailableError(
                f"Request to Ollama failed: {exc}"
            ) from exc

        if response.status_code == 404:
            response.close()
            raise ModelNotFoundError(
                f"Model '{self.config.model}' was not found on this Ollama "
                f"server ({self.config.base_url}). Pull it first."
            )

        if response.status_code != 200:
            body = response.text[:200]
            response.close()
            raise ProviderResponseError(
                f"Ollama returned HTTP {response.status_code}: {body}"
            )

        try:
            for line in response.iter_lines():
                if not line:
                    continue
                try:
                    data = json.loads(line)
                except ValueError as exc:
                    raise ProviderResponseError(
                        "Ollama streamed a line that was not valid JSON."
                    ) from exc

                if not isinstance(data, dict):
                    raise ProviderResponseError(
                        "Ollama streamed a line that was not a JSON object."
                    )

                message = data.get("message")
                delta_content = ""
                if isinstance(message, dict) and isinstance(message.get("content"), str):
                    delta_content = message["content"]

                raw_tool_calls = message.get("tool_calls") if isinstance(message, dict) else None
                is_tool_call = bool(raw_tool_calls)
                if is_tool_call and tools:
                    tool_calls_final = _parse_ollama_tool_calls(raw_tool_calls)

                if delta_content:
                    if ttft is None:
                        ttft = time.monotonic() - start
                    accumulated_content.append(delta_content)

                done = bool(data.get("done"))
                if not done:
                    yield StreamChunk(content=delta_content, is_tool_call=is_tool_call, done=False)
                    continue

                duration_seconds = time.monotonic() - start
                prompt_tokens = data.get("prompt_eval_count")
                eval_tokens = data.get("eval_count")
                final_response = ModelResponse(
                    content="".join(accumulated_content),
                    model=data.get("model", self.config.model),
                    provider="ollama",
                    prompt_tokens=prompt_tokens if isinstance(prompt_tokens, int) else None,
                    eval_tokens=eval_tokens if isinstance(eval_tokens, int) else None,
                    duration_seconds=duration_seconds,
                    tool_calls=(tool_calls_final if tools else None),
                )
                yield StreamChunk(
                    content=delta_content,
                    is_tool_call=bool(tool_calls_final),
                    done=True,
                    final_response=final_response,
                    ttft_seconds=ttft,
                )
                return

            # M32 D5: the connection closed (or Ollama stopped sending
            # lines) without ever sending a "done": true line - never
            # silently treat this as a normal, complete response (which
            # would hand a caller an incomplete `final_response=None`
            # via no terminal chunk at all). An explicit, honest failure
            # here matches this provider's own non-streaming complete()
            # discipline - see its own "no message.content" check.
            raise ProviderResponseError(
                "Ollama's stream ended without a final done=true line - "
                "the response is incomplete."
            )
        finally:
            response.close()

    def _model_max_context(self, response) -> Optional[int]:
        """M21: the model's own trained/supported context length, parsed
        from the SAME /api/tags body describe() already fetches for
        availability - genuinely free, contrary to this method's previous
        claim that getting this number would cost a second network call.
        Real Ollama's /api/tags response nests it at
        models[].details.context_length; verified against a live server
        during the M21 audit. Returns None on any shape mismatch (a fake/
        mocked response in a test, a future Ollama version that moves the
        field) rather than guessing - never raises."""

        try:
            body = response.json()
        except Exception:
            return None

        if not isinstance(body, dict):
            return None

        for entry in body.get("models", []):
            if not isinstance(entry, dict) or entry.get("name") != self.config.model:
                continue
            details = entry.get("details")
            if isinstance(details, dict):
                value = details.get("context_length")
                if isinstance(value, int):
                    return value

        return None

    def describe(self) -> ModelProviderStatus:
        """A lightweight GET against Ollama's /api/tags - never a real
        completion (see ModelProvider.describe's contract) - bounded to
        DEFAULT_HEALTH_CHECK_TIMEOUT_SECONDS regardless of how long
        config.timeout_seconds allows a real completion to take, so a
        self-knowledge query never hangs waiting on the slower budget a
        real request is allowed.

        M21: context_window now reports the actual configured num_ctx
        (self.config.context_tokens) that every real complete() call sends
        - previously always None, which is what let a real 4096-token
        runtime default go unnoticed and undocumented for as long as it
        did (see the M21 audit). When the same /api/tags body also reports
        this model's own maximum context (see _model_max_context - free,
        no second network call, correcting this method's previous claim
        that it would cost one), a configured value larger than that
        maximum is surfaced honestly in `detail` rather than silently
        accepted."""

        health_check_timeout = min(
            self.config.timeout_seconds,
            DEFAULT_HEALTH_CHECK_TIMEOUT_SECONDS,
        )

        available = False
        detail = None
        model_max_context = None

        try:
            response = requests.get(
                f"{self.config.base_url.rstrip('/')}/api/tags",
                timeout=health_check_timeout,
            )

            if response.status_code == 200:
                available = True
                model_max_context = self._model_max_context(response)
            else:
                detail = (
                    f"Ollama returned HTTP {response.status_code} at "
                    f"{self.config.base_url}."
                )

        except requests.exceptions.Timeout:
            detail = (
                "Ollama did not respond within "
                f"{health_check_timeout}s at {self.config.base_url}."
            )

        except requests.exceptions.ConnectionError:
            detail = (
                f"Could not reach Ollama at {self.config.base_url}. "
                "Is it running?"
            )

        except requests.exceptions.RequestException as exc:
            detail = f"Request to Ollama failed: {exc}"

        if (
            model_max_context is not None
            and self.config.context_tokens > model_max_context
        ):
            warning = (
                f"configured context_tokens ({self.config.context_tokens}) "
                f"exceeds this model's maximum supported context "
                f"({model_max_context})."
            )
            detail = f"{detail} {warning}" if detail else warning

        return ModelProviderStatus(
            provider_name="ollama",
            model_name=self.config.model,
            location=_location_from_base_url(self.config.base_url),
            context_window=self.config.context_tokens,
            supports=("text",),
            available=available,
            detail=detail,
        )

    def list_installed_models(self) -> list[str]:
        """The real model names this Ollama server actually has pulled -
        the same /api/tags endpoint describe() probes, parsed for its
        models[].name field instead of just checking HTTP 200. This is
        what lets a caller distinguish "the Ollama daemon is reachable"
        (describe().available) from "this specific configured model is
        one Ollama can actually serve" - the daemon can be reachable
        while the configured/default model was never pulled, and until
        this method existed nothing surfaced that distinction. Returns an
        empty list on any failure (unreachable, malformed body) - never
        raises, never guesses a name that might not be real."""

        try:
            response = requests.get(
                f"{self.config.base_url.rstrip('/')}/api/tags",
                timeout=min(self.config.timeout_seconds, DEFAULT_HEALTH_CHECK_TIMEOUT_SECONDS),
            )
            if response.status_code != 200:
                return []
            body = response.json()
        except Exception:
            return []

        if not isinstance(body, dict):
            return []

        names = []
        for entry in body.get("models", []):
            if isinstance(entry, dict) and isinstance(entry.get("name"), str):
                names.append(entry["name"])
        return names

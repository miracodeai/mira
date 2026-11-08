"""Provider protocol — the interface that all LLM backends must satisfy."""

from __future__ import annotations

import logging
import os
from typing import ClassVar, Protocol, runtime_checkable

import httpx
from tenacity import retry, retry_if_exception, stop_after_attempt, wait_exponential

from mira.config import LLMConfig
from mira.exceptions import LLMError, NonRetriableLLMError, StructuredOutputError
from mira.llm import provider_profiles as profiles
from mira.llm.tool_schemas import SUBMIT_REVIEW_TOOL, SUBMIT_WALKTHROUGH_TOOL

logger = logging.getLogger(__name__)


@runtime_checkable
class LLMProviderProtocol(Protocol):
    """Structural interface for LLM providers.

    Both the OpenAI-compatible provider and direct-API providers
    (Bedrock, Anthropic, Vertex, etc.) satisfy this protocol.

    Capability annotations:
        supports_json_mode: Provider natively supports response_format=json_object.
        supports_tool_calling: Provider supports function/tool calling.
    """

    supports_json_mode: bool
    supports_tool_calling: bool

    total_prompt_tokens: int
    total_completion_tokens: int

    async def complete(
        self,
        messages: list[dict[str, str]],
        json_mode: bool = True,
        temperature: float | None = None,
        max_tokens: int | None = None,
    ) -> str: ...

    async def complete_with_tools(
        self,
        messages: list[dict[str, str]],
        tools: list[dict],
        temperature: float | None = None,
        force_tool: str | None = None,
    ) -> str: ...

    async def complete_agentic(
        self,
        messages: list,
        tools: list[dict],
        temperature: float | None = None,
    ) -> dict: ...

    async def review(
        self, messages: list[dict[str, str]], temperature: float | None = None
    ) -> str: ...

    async def walkthrough(self, messages: list[dict[str, str]]) -> str: ...

    def count_tokens(self, text: str) -> int: ...

    @property
    def usage(self) -> dict[str, int]: ...


# ── Module-level helpers (shared by both providers) ─────────────────


def _get_api_key(config: LLMConfig, profile: dict | None = None) -> str:
    """Resolve the API key for the configured endpoint.

    Reads `config.api_key_env` first, then the matched provider profile's
    `api_key_env`, then the legacy `OPENROUTER_API_KEY` / `OPENAI_API_KEY`
    lookup for backward compatibility. If `api_key_env` is explicitly "" the
    empty string is returned without error — useful for local endpoints
    (Ollama, llama.cpp server) that don't require auth.
    """
    if config.api_key_env == "":
        return ""
    key = os.environ.get(config.api_key_env, "")
    if not key and profile and profile.get("api_key_env"):
        key = os.environ.get(profile["api_key_env"], "")
    if not key:
        # Back-compat with pre-`api_key_env` setups.
        key = os.environ.get("OPENROUTER_API_KEY") or os.environ.get("OPENAI_API_KEY", "")
    if not key:
        raise LLMError("no_api_key", api_key_env=config.api_key_env)
    return key


def _strip_model_prefix(model: str, base_url: str) -> str:
    """Apply the endpoint's model-prefix policy from its provider profile.

    'keep' (OpenRouter) routes on the full `vendor/model` string and only sheds
    a redundant self-prefix (`openrouter/…`). 'strip' (the default for other
    endpoints) sends the bare model name (e.g. 'minimax/MiniMax-M2.7' →
    'MiniMax-M2.7').
    """
    profile = profiles.resolve(base_url)
    if profile.get("model_prefix") == "keep":
        self_prefix = f"{profile['name']}/"
        return model[len(self_prefix) :] if model.startswith(self_prefix) else model
    return model.split("/", 1)[1] if "/" in model else model


def _retriable(exception: BaseException) -> bool:
    """Return True for transient errors; False for 4xx and semantic failures."""
    if isinstance(exception, (NonRetriableLLMError, StructuredOutputError)):
        return False
    return isinstance(
        exception,
        (httpx.TimeoutException, httpx.NetworkError, LLMError),
    )


# Output budget for the one retry after a response was cut off at ``max_tokens``
# when the configured budget was lower than this (the default is this value,
# which the published benchmark ran with).
BUDGET_RETRY_TOKENS = 16384
# Budget an endpoint is retried at after rejecting the configured one; every
# model Mira has been run on accepts it.
BUDGET_FLOOR_TOKENS = 4096


def _exception_excerpt(error: BaseException, limit: int = 300) -> str:
    """Short, single-line error text safe to put in a diagnostic message."""
    text = " ".join(str(error).split())
    return text[:limit] + ("…" if len(text) > limit else "")


# ── Shared base for OpenAI-compatible providers ─────────────────────


class OpenAICompatibleProvider:
    """Protocol-agnostic base for OpenAI-compatible API providers.

    Captures the code shared by ``LLMProvider`` (chat/completions) and
    ``ResponsesProvider`` (/responses protocol): retry setup, header
    building, reasoning, fallback model logic, token accounting, and the
    public API surface.  Protocol-specific paths (URL, input/output
    format, tool transformation) remain in each subclass.
    """

    supports_json_mode: ClassVar[bool] = True
    supports_tool_calling: ClassVar[bool] = True

    def __init__(self, config: LLMConfig) -> None:
        self.config = config
        self.profile = profiles.resolve(config.base_url)
        self.total_prompt_tokens = 0
        self.total_completion_tokens = 0
        # Prompt-cache activity reported by the endpoint (subset of prompt tokens).
        self.total_cache_read_tokens = 0
        self.total_cache_write_tokens = 0
        self._no_forced_tool_choice: set[str] = set()
        self._no_reasoning: set[str] = set()
        # Per-model output budget after an endpoint rejected the configured one.
        self._budget_caps: dict[str, int] = {}

        # Apply retry decorator imperatively so it reads config values
        # (max_retries, retry_min_wait, retry_max_wait) at instance time.
        self._retry = retry(
            stop=stop_after_attempt(config.max_retries),
            wait=wait_exponential(
                multiplier=1,
                min=config.retry_min_wait,
                max=config.retry_max_wait,
            ),
            retry=retry_if_exception(_retriable),
            reraise=True,
        )
        # Decorate the concrete subclass methods with retry logic.
        self._call_llm = self._retry(self._call_llm)
        self._call_llm_with_tools = self._retry(self._call_llm_with_tools)
        self._call_llm_agentic = self._retry(self._call_llm_agentic)

    # ── Shared helpers ─────────────────────────────────────────────

    def _build_headers(self) -> dict[str, str]:
        """Build request headers: Content-Type, optional Bearer auth, and any
        provider-specific extras from the profile. Authorization is omitted
        entirely if the endpoint needs no key (Ollama, llama.cpp, etc.)."""
        if hasattr(self, "_cached_headers"):
            return dict(self._cached_headers)
        headers: dict[str, str] = {"Content-Type": "application/json"}
        key = _get_api_key(self.config, self.profile)
        if key:
            headers["Authorization"] = f"Bearer {key}"
        headers.update(self.profile.get("extra_headers", {}))
        self._cached_headers = headers
        return dict(headers)

    def _max_tokens_field(self) -> str:
        """Name of the Chat Completions output-token field for this profile."""
        return self.profile.get("max_tokens_field", "max_tokens")

    @staticmethod
    def _reasoning_requested(body: dict) -> bool:
        """Whether the request asked the model to think (rather than not, or nothing)."""
        if body.get("reasoning_effort"):
            return True
        reasoning = body.get("reasoning")
        if isinstance(reasoning, dict):
            return reasoning.get("enabled") is not False
        thinking = body.get("thinking")
        return isinstance(thinking, dict) and thinking.get("type") == "enabled"

    def _budget_exhausted_retry(self, body: dict, data: dict) -> dict | None:
        """Return a retry body when the model hit the output budget before finishing.

        Thinking models count their reasoning against ``max_tokens``, so a
        reply cut off at the budget comes in two shapes. The answer itself was
        too long: retry with the larger budget. The model spent the budget
        thinking and never got to the answer: a larger budget does not help
        (DeepSeek v4.1 flash spent all of 16k reasoning on two real PRs), so
        the retry also turns thinking off where the provider has a switch for
        it, and the same prompt then completes in seconds. Returns ``None``
        when the response finished normally or nothing could change.
        """
        choice = (data.get("choices") or [{}])[0]
        if choice.get("finish_reason") != "length":
            return None
        model = str(body.get("model"))
        field = self._max_tokens_field()
        current = int(body.get(field) or self.config.max_tokens)
        target = min(BUDGET_RETRY_TOKENS, self._budget_caps.get(model, 10**9))
        usage = data.get("usage") or {}
        details = usage.get("completion_tokens_details") or {}
        completion_tokens = int(usage.get("completion_tokens") or 0)
        reasoning_tokens = int(details.get("reasoning_tokens") or 0)

        raise_budget = current < target
        thinking_ate_it = reasoning_tokens > 0 and reasoning_tokens * 10 >= completion_tokens * 9
        stop_thinking = (
            thinking_ate_it
            and self._reasoning_requested(body)
            and bool(self.profile.get("reasoning_off_payload"))
        )
        if not raise_budget and not stop_thinking:
            return None

        retry = dict(body)
        changes: list[str] = []
        if raise_budget:
            retry[field] = target
            changes.append(f"budget {target}")
        if stop_thinking:
            self._remove_reasoning(retry)
            retry.update(self.profile["reasoning_off_payload"])
            changes.append("thinking off")
        logger.warning(
            "Model %s hit its %d-token output budget before finishing "
            "(completion_tokens=%s, reasoning_tokens=%s); retrying once with %s",
            model,
            current,
            completion_tokens,
            reasoning_tokens,
            ", ".join(changes),
        )
        return retry

    def _cap_output_budget(self, body: dict) -> None:
        """Lower the request's output budget to what this model accepted before."""
        cap = self._budget_caps.get(str(body.get("model")))
        if cap is None:
            return
        field = self._max_tokens_field()
        if int(body.get(field) or 0) > cap:
            body[field] = cap

    def _lower_rejected_budget(self, body: dict, error_text: str) -> bool:
        """After a 400 about the output budget, lower it in place and remember.

        Endpoints word it differently ("max_tokens is too large", "maximum
        context length", "output tokens"), so match loosely but only when the
        request actually carried more than the floor. Returns True when the
        body was changed and the request should be sent again.
        """
        text = error_text.lower()
        if not any(
            marker in text
            for marker in ("max_tokens", "max_completion_tokens", "context length", "output tokens")
        ):
            return False
        field = self._max_tokens_field()
        current = int(body.get(field) or 0)
        if current <= BUDGET_FLOOR_TOKENS:
            return False
        logger.warning(
            "Endpoint rejected an output budget of %d for %s; retrying at %d and keeping it there",
            current,
            body.get("model"),
            BUDGET_FLOOR_TOKENS,
        )
        self._budget_caps[str(body.get("model"))] = BUDGET_FLOOR_TOKENS
        body[field] = BUDGET_FLOOR_TOKENS
        return True

    @staticmethod
    def _remove_reasoning(body: dict) -> None:
        """Drop every reasoning-shaped field Mira may have added."""
        for key in ("reasoning", "reasoning_effort", "thinking", "enable_thinking"):
            body.pop(key, None)

    @staticmethod
    def _has_reasoning(body: dict) -> bool:
        return any(
            key in body for key in ("reasoning", "reasoning_effort", "thinking", "enable_thinking")
        )

    def _apply_reasoning_off(self, body: dict, protocol: str = "chat") -> None:
        """Apply a profile's explicit "thinking off" payload, if it has one.

        Chat and Responses disable thinking differently, so the Responses
        payload is separate. Providers with no documented disable remain a
        no-op (their default applies). So does a model that already refused
        reasoning settings on a provider whose effort and off switch are one
        unified parameter (OpenRouter's ``reasoning``): it takes neither.
        """
        if body.get("model") in self._no_reasoning and not self.profile.get("reasoning_on_payload"):
            return
        key = (
            "reasoning_off_payload_responses"
            if protocol == "responses"
            else "reasoning_off_payload"
        )
        body.update(self.profile.get(key, {}))

    def _drop_rejected_reasoning(self, body: dict, api_model: str, protocol: str = "chat") -> None:
        """Strip the reasoning fields a 400 just refused and remember the model.

        Providers with a separate thinking toggle (DeepSeek's ``thinking``)
        get the explicit off payload back after the effort field is refused,
        or default-on thinking would stay in place. Providers whose effort
        and off switch are one unified parameter (OpenRouter's ``reasoning``)
        have just said the model takes neither: a model whose reasoning is
        mandatory refuses the off payload, a model without reasoning refuses
        the effort, and ``_apply_reasoning_off`` sends both nothing from now on.
        """
        logger.info("Model %s rejected reasoning settings; retrying without them", api_model)
        self._remove_reasoning(body)
        self._no_reasoning.add(api_model)
        self._apply_reasoning_off(body, protocol)

    def _apply_reasoning(self, body: dict, protocol: str = "chat") -> None:
        """Add the provider's documented reasoning toggle and effort field.

        Chat Completions uses the top-level ``reasoning_effort`` field on
        OpenAI and most compatible endpoints; OpenRouter accepts that same
        shorthand. Responses API uses ``reasoning.effort``. Providers that
        need a separate toggle (DeepSeek) get it from the profile.

        Anthropic-style models reject a custom ``temperature`` while thinking
        is on, so we drop it when reasoning is applied. When reasoning is off
        or was previously rejected for this model, the profile's explicit off
        payload is applied instead.
        """
        effort = self.config.reasoning_effort
        if not effort or effort == "off" or body.get("model") in self._no_reasoning:
            self._apply_reasoning_off(body, protocol)
            return
        effort = self.profile.get("reasoning_effort_map", {}).get(effort, effort)
        if protocol == "responses":
            body["reasoning"] = {"effort": effort}
        else:
            body["reasoning_effort"] = effort
            body.update(self.profile.get("reasoning_on_payload", {}))
        body.pop("temperature", None)

    def _account_usage(self, data: dict) -> None:
        """Accumulate token counts. Default: chat/completions key names.

        Subclasses override when the API uses different keys
        (e.g. Responses API uses ``input_tokens`` / ``output_tokens``).
        """
        usage = data.get("usage")
        if usage:
            self.total_prompt_tokens += usage.get("prompt_tokens", 0)
            self.total_completion_tokens += usage.get("completion_tokens", 0)
            details = usage.get("prompt_tokens_details") or {}
            cache_read = details.get("cached_tokens") or 0
            cache_write = details.get("cache_write_tokens") or 0
            self.total_cache_read_tokens += cache_read
            self.total_cache_write_tokens += cache_write
            if cache_read or cache_write:
                logger.info(
                    "LLM prompt cache: read=%d write=%d prompt=%d",
                    cache_read,
                    cache_write,
                    usage.get("prompt_tokens", 0),
                )

    @staticmethod
    def _handle_error(resp: httpx.Response) -> None:
        """Raise LLMError or NonRetriableLLMError on non-200 responses."""
        if resp.status_code != 200:
            if 400 <= resp.status_code < 500 and resp.status_code != 429:
                raise NonRetriableLLMError("api_error", status=resp.status_code, body=resp.text)
            raise LLMError("api_error", status=resp.status_code, body=resp.text)

    # ── Subclass hooks (abstract) ──────────────────────────────────

    async def _call_llm(
        self,
        model: str,
        messages: list[dict[str, str]],
        json_mode: bool,
        temperature: float | None = None,
        max_tokens: int | None = None,
    ) -> str:
        raise NotImplementedError

    async def _call_llm_with_tools(
        self,
        model: str,
        messages: list[dict[str, str]],
        tools: list[dict],
        temperature: float | None = None,
        force_tool: str | None = None,
    ) -> str:
        raise NotImplementedError

    async def _call_llm_agentic(
        self,
        model: str,
        messages: list,
        tools: list[dict],
        temperature: float | None = None,
    ) -> dict:
        raise NotImplementedError

    # ── Public API (shared across chat and responses providers) ─────

    async def complete(
        self,
        messages: list[dict[str, str]],
        json_mode: bool = True,
        temperature: float | None = None,
        max_tokens: int | None = None,
    ) -> str:
        """Complete a prompt using JSON mode, with fallback model support."""
        try:
            return await self._call_llm(
                self.config.model,
                messages,
                json_mode,
                temperature=temperature,
                max_tokens=max_tokens,
            )
        except NonRetriableLLMError:
            raise
        except Exception as primary_err:
            if self.config.fallback_model:
                logger.warning(
                    "Primary model %s failed (%s), trying fallback %s",
                    self.config.model,
                    primary_err,
                    self.config.fallback_model,
                )
                try:
                    return await self._call_llm(
                        self.config.fallback_model,
                        messages,
                        json_mode,
                        temperature=temperature,
                        max_tokens=max_tokens,
                    )
                except Exception as fallback_err:
                    raise LLMError(
                        "both_models_failed",
                        primary_model=self.config.model,
                        fallback_model=self.config.fallback_model,
                        error=fallback_err,
                    ) from fallback_err
            raise LLMError(
                "completion_failed", model=self.config.model, error=primary_err
            ) from primary_err

    async def complete_with_tools(
        self,
        messages: list[dict[str, str]],
        tools: list[dict],
        temperature: float | None = None,
        force_tool: str | None = None,
    ) -> str:
        """Complete a prompt using tool calling for structured output.

        ``force_tool`` names the tool to force and switches on strict structured
        output: a successful response that contains prose instead of that tool
        call raises ``StructuredOutputError``. Without it the historical text
        fallback is preserved for callers that tolerate prose.
        """
        try:
            return await self._call_llm_with_tools(
                self.config.model,
                messages,
                tools,
                temperature=temperature,
                force_tool=force_tool,
            )
        except NonRetriableLLMError:
            raise
        except Exception as primary_err:
            if self.config.fallback_model:
                logger.warning(
                    "Primary model %s failed (%s), trying fallback %s",
                    self.config.model,
                    primary_err,
                    self.config.fallback_model,
                )
                try:
                    return await self._call_llm_with_tools(
                        self.config.fallback_model,
                        messages,
                        tools,
                        temperature=temperature,
                        force_tool=force_tool,
                    )
                except Exception as fallback_err:
                    if isinstance(primary_err, StructuredOutputError) or isinstance(
                        fallback_err, StructuredOutputError
                    ):
                        raise StructuredOutputError(
                            "structured_output",
                            model=self.config.fallback_model,
                            tool=force_tool or "structured tool",
                            excerpt=_exception_excerpt(fallback_err),
                        ) from fallback_err
                    raise LLMError(
                        "both_models_failed",
                        primary_model=self.config.model,
                        fallback_model=self.config.fallback_model,
                        error=fallback_err,
                    ) from fallback_err
            if isinstance(primary_err, StructuredOutputError):
                raise
            raise LLMError(
                "tool_call_failed", model=self.config.model, error=primary_err
            ) from primary_err

    async def complete_agentic(
        self,
        messages: list,
        tools: list[dict],
        temperature: float | None = None,
    ) -> dict:
        """Single hop of an agentic loop. Returns the assistant message dict."""
        try:
            return await self._call_llm_agentic(
                self.config.model, messages, tools, temperature=temperature
            )
        except NonRetriableLLMError:
            raise
        except Exception as primary_err:
            if self.config.fallback_model:
                logger.warning(
                    "Primary model %s failed (%s), trying fallback %s",
                    self.config.model,
                    primary_err,
                    self.config.fallback_model,
                )
                try:
                    return await self._call_llm_agentic(
                        self.config.fallback_model, messages, tools, temperature=temperature
                    )
                except Exception as fallback_err:
                    raise LLMError(
                        "both_models_failed",
                        primary_model=self.config.model,
                        fallback_model=self.config.fallback_model,
                        error=fallback_err,
                    ) from fallback_err
            raise LLMError(
                "agentic_failed", model=self.config.model, error=primary_err
            ) from primary_err

    async def review(self, messages: list[dict[str, str]], temperature: float | None = None) -> str:
        """Submit a review using tool calling."""
        return await self.complete_with_tools(
            messages, tools=[SUBMIT_REVIEW_TOOL], temperature=temperature
        )

    async def walkthrough(self, messages: list[dict[str, str]]) -> str:
        """Submit a walkthrough using tool calling."""
        return await self.complete_with_tools(messages, tools=[SUBMIT_WALKTHROUGH_TOOL])

    def count_tokens(self, text: str) -> int:
        """Estimate token count. Uses ~4 chars per token heuristic."""
        return len(text) // 4

    @property
    def usage(self) -> dict[str, int]:
        return {
            "prompt_tokens": self.total_prompt_tokens,
            "completion_tokens": self.total_completion_tokens,
            "total_tokens": self.total_prompt_tokens + self.total_completion_tokens,
        }

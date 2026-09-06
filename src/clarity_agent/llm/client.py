"""Abstract base class for low-level LLM clients.

An ``LLMClient`` wraps a single provider's message-creation API and returns
normalized :class:`~clarity_agent.llm.types.LLMResponse` objects. This is a
low-level interface used with raw LLM chat completion API's; the rest of the
clarity-agent consumes this via the higher-level ChatBackend interface.
"""

from __future__ import annotations

from abc import ABC, abstractmethod
from collections.abc import Callable
from typing import Any, ClassVar

from clarity_agent.llm.model_catalog import build_catalog
from clarity_agent.llm.types import (
    LLMResponse,
    ModelCatalog,
    StructuredToolCallback,
    TextDeltaCallback,
    ToolCallback,
    UsageCallback,
)

# ---------------------------------------------------------------------------
# Tool-detail extraction (shared by LLMClient callbacks and ChatBackend)
# ---------------------------------------------------------------------------

def truncate(val: str, limit: int = 80) -> str:
    return val[:limit] + "..." if len(val) > limit else val

# Tier 1: tool-specific formatters for the most useful summary per tool.
_TOOL_DETAIL_EXTRACTORS: dict[str, Callable[[dict], str]] = {
    "Bash": lambda inp: f"{inp.get('description', '')}: {inp.get('command', '')}",
    "Edit": lambda inp: inp.get("file_path", ""),
    "Read": lambda inp: inp.get("file_path", ""),
    "Task": lambda inp: inp.get("description", ""),
    "WebFetch": lambda inp: inp.get("url", ""),
    "WebSearch": lambda inp: inp.get("query", ""),
}

# Tier 2: ordered list of well-known input keys.  The first match wins.
_DETAIL_KEYS: list[str] = [
    "file_path", "command", "pattern", "query",
    "url", "path", "title", "description", "prompt",
]


def extract_tool_detail(name: str, tool_input: dict[str, Any]) -> str:
    """Return a short human-readable summary of a tool invocation.

    Used by :class:`LLMClient` and :class:`ChatBackend` callbacks to
    produce a compact description of what a tool call does.

    Resolution order:

    1. **Tool-specific** — a custom formatter for well-known tools
       (``Bash``, ``Edit``, ``Read``, …).
    2. **Well-known keys** — the first matching key from a priority list
       (``file_path``, ``command``, ``title``, …).
    3. **Generic** — parameter names only (avoids leaking values).
    """
    # Tier 1 – tool-specific
    if name in _TOOL_DETAIL_EXTRACTORS:
        return _TOOL_DETAIL_EXTRACTORS[name](tool_input)

    # Tier 2 – well-known keys
    for key in _DETAIL_KEYS:
        if key in tool_input:
            return str(tool_input[key])

    # Tier 3 – generic: show parameter names (avoids leaking values)
    if tool_input:
        return f"({', '.join(tool_input.keys())})"
    return ""


class LLMClient(ABC):
    """Async client for creating LLM messages.

    Implementations translate between the canonical request/response
    format and a specific provider's API (Anthropic, OpenAI, Azure, …).

    Tool definitions use the Anthropic-style canonical format::

        {
            "name": "tool_name",
            "description": "What the tool does",
            "input_schema": { … JSON Schema … },
        }

    Non-Anthropic backends translate this in their ``_create_message``
    implementation.

    Subclasses should declare :attr:`RECOMMENDED_MODELS`, mapping the
    ``"default"``/``"deep"``/``"fast"`` highlight roles to concrete
    model strings for their provider.

    **Callbacks**

    Every tool-use block in a response is automatically printed to
    stdout (``[Tool] name -> detail``).  Set :attr:`on_tool_use` for
    additional handling (e.g. forwarding events to a web client).
    """

    RECOMMENDED_MODELS: ClassVar[dict[str, str]] = {}
    """Provider-specific mapping from highlight role to model string.

    Declares which concrete models fill the ``"default"``, ``"deep"``
    and ``"fast"`` roles.  Used to build the model catalog and to pick
    a model when the user hasn't; :meth:`create_message` always
    receives a concrete model, chosen by the backend above.
    """

    MODEL_CONTEXT_WINDOWS: ClassVar[dict[str, int]] = {}
    """Provider-specific mapping from concrete model strings to their
    context-window size in tokens.  Co-located with
    :attr:`RECOMMENDED_MODELS`; consumed via :meth:`ChatBackend.context_window_for`
    when the :class:`ClientChatBackend` wrapper forwards from its
    wrapped client.
    """

    on_tool_use: ToolCallback | None = None
    """Optional callback fired for each tool-use block in a response.

    This is *in addition to* the default ``[Tool]`` print.  Use it
    for things like forwarding events to a web UI.  Receives
    flattened ``(name, detail)`` strings — use :attr:`on_tool_call`
    if you need the structured :class:`ToolUseBlock` (id + input
    dict) for transcript persistence or replay.
    """

    on_tool_call: StructuredToolCallback | None = None
    """Optional callback fired with the structured :class:`ToolUseBlock`.

    Fires alongside :attr:`on_tool_use` in :meth:`create_message`.
    Consumers that need round-trippable tool data (the transcript
    layer, the message-replay path) subscribe here; UI surfaces
    that just want a display string keep using :attr:`on_tool_use`.
    """

    on_text_delta: TextDeltaCallback | None = None
    """Optional callback fired for each text chunk during streaming."""

    on_usage: UsageCallback | None = None
    """Optional callback fired when a response includes token usage data."""

    _suppress_tool_output: bool = False
    """When True, :meth:`create_message` skips the ``[Tool]`` print and
    ``on_tool_use`` callback.  Set by :class:`ChatBackend` tool loops
    that provide a handler which does its own output."""

    _callbacks_fired_inline: bool = False
    """Set by :meth:`_create_message` implementations that fire the
    tool-use callbacks *during* streaming (currently only
    :class:`AnthropicClient`).  Tells the post-call paths in both
    :meth:`create_message` and :class:`ClientChatBackend.chat` to
    skip their re-firing — without this guard, each tool call would
    be reported twice: once live mid-stream, again at end-of-round.

    Reset to ``False`` at the start of each :meth:`create_message`
    invocation so the inline path opts in per-call."""

    @classmethod
    def builtin_catalog(cls) -> ModelCatalog:
        """Models this class knows about, without any network call.

        Derived from :attr:`RECOMMENDED_MODELS` and
        :attr:`MODEL_CONTEXT_WINDOWS` — the model names this codebase
        has already vetted — so it can't drift from them the way a
        separately maintained list would.

        A classmethod because a catalog describes the *provider*, not
        a particular client: callers need it before credentials are
        resolved, and it's the fallback whenever a live listing fails.
        Subclasses override only to change the framing (Azure marks
        itself ``free_form``), not the contents.
        """
        return build_catalog(
            recommended=cls.RECOMMENDED_MODELS,
            context_windows=cls.MODEL_CONTEXT_WINDOWS,
        )

    async def fetch_models(self) -> ModelCatalog:
        """List the models these credentials can reach.

        The default is :meth:`builtin_catalog` — correct for providers
        with no listing endpoint.  Subclasses that can enumerate
        override this and are free to raise on failure:
        :func:`~clarity_agent.llm.factory.fetch_model_catalog` catches,
        falls back to the built-in catalog, and attaches the error.
        """
        return self.builtin_catalog()

    async def create_message(
        self,
        *,
        messages: list[dict[str, Any]],
        model: str,
        max_tokens: int = 4096,
        system: str | None = None,
        tools: list[dict[str, Any]] | None = None,
    ) -> LLMResponse:
        """Create a single LLM response and fire any registered callbacks.

        This is the public entry point.  Subclasses implement the
        provider-specific logic in :meth:`_create_message`.

        Args:
            messages: Conversation history in Anthropic message format
                (``[{"role": "user"|"assistant", "content": …}, …]``).
            model: Model identifier (e.g. ``"claude-sonnet-4-5-20250929"``).
            max_tokens: Maximum tokens in the response.
            system: Optional system prompt.
            tools: Optional list of tool definitions in canonical format.

        Returns:
            A normalized :class:`LLMResponse`.
        """
        # Per-call reset of the inline-fired flag.  Streaming
        # implementations that fire callbacks mid-response set this
        # to ``True`` before returning; the post-call loop below
        # then skips its own firing to avoid duplicates.
        self._callbacks_fired_inline = False
        response = await self._create_message(
            messages=messages,
            model=model,
            max_tokens=max_tokens,
            system=system,
            tools=tools,
        )
        if not self._suppress_tool_output and not self._callbacks_fired_inline:
            for tc in response.tool_calls:
                detail = extract_tool_detail(tc.name, tc.input)
                print(f"  [Tool] {tc.name} -> {truncate(detail)}")
                if self.on_tool_use:
                    self.on_tool_use(tc.name, detail)
                # Structured callback for transcript persistence —
                # preserves the provider-assigned id + structured
                # input dict that on_tool_use's flattened detail
                # discards.  All non-SDK backends (Anthropic API,
                # OpenAI, Azure Inference, ...) go through this
                # ``create_message`` method, so wiring it once here
                # covers them all.
                if self.on_tool_call:
                    self.on_tool_call(tc)
        if response.usage and self.on_usage:
            self.on_usage(response.usage)
        return response

    @abstractmethod
    async def _create_message(
        self,
        *,
        messages: list[dict[str, Any]],
        model: str,
        max_tokens: int = 4096,
        system: str | None = None,
        tools: list[dict[str, Any]] | None = None,
    ) -> LLMResponse:
        """Provider-specific message creation (override in subclasses).

        Same parameters as :meth:`create_message`.  Subclasses should
        return a normalized :class:`LLMResponse`; callback dispatch is
        handled by the public method.
        """
        ...

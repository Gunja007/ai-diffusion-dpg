"""
MergedConfig — strict schema for the Agent Core merged runtime config.

Merged config = dev-kit/dpg/agent_core.yaml (framework defaults)
                deep-merged with a domain YAML
                (e.g. dev-kit/configs/kkb/agent_core.yaml).

Every model sets ``extra="forbid"``: unknown keys at any nesting level
fail at startup with a pydantic ValidationError, not at first request.

Open-map sub-sections are modelled as ``dict[str, <inner>]``:

- ``entity_to_profile_field`` — entity_name → profile_field_name
- ``preprocessing.nlu_processor.signal_intents`` — intent → signal_type
- ``connectors.*.[].input_schema.properties`` — JSON Schema property map

Belongs to the Agent Core DPG block.
"""
from __future__ import annotations

from enum import Enum
from typing import Any, Literal, Optional

from pydantic import BaseModel, ConfigDict, Field, field_validator


# ---------------------------------------------------------------------------
# Enums
# ---------------------------------------------------------------------------


class RoutingOperator(str, Enum):
    """Comparison operator for a routing condition."""

    eq = "eq"
    not_eq = "not_eq"
    gt = "gt"
    lt = "lt"
    in_ = "in"


class SpecialHandler(str, Enum):
    """Framework-level subagent handler that bypasses normal LLM flow."""

    hitl = "hitl"
    whatsapp_handoff = "whatsapp_handoff"


class AssemblyMode(str, Enum):
    """Turn assembly mode (cosmetic label, channel-specific)."""

    streaming = "streaming"
    batch = "batch"


# ---------------------------------------------------------------------------
# Framework / infrastructure sections
# ---------------------------------------------------------------------------


class ServerConfig(BaseModel):
    """Uvicorn bind settings for the Agent Core entry point."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    host: str = "0.0.0.0"
    port: int = Field(default=8000, gt=0, lt=65536)


class ClientConfig(BaseModel):
    """Generic HTTP client config for an inter-service call."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    endpoint: str
    timeout_ms: int = Field(default=5000, gt=0)


class CheckOutputBatchConfig(BaseModel):
    """Trust Layer ``/check/output`` batching policy for streaming turns.

    During SSE streaming, sentences are buffered and submitted to Trust Layer
    as a single concatenated check whenever the buffer reaches ``max_sentences``
    or ``max_interval_ms`` has elapsed since the first buffered sentence —
    whichever happens first. On ``block`` / ``escalate`` verdicts the entire
    pending batch is replaced with the configured fallback message; sentences
    already emitted in earlier batches are not retracted.

    Attributes:
        enabled: When False, every sentence is checked individually
            (legacy behaviour).
        max_sentences: Flush trigger by buffer size (>=1).
        max_interval_ms: Flush trigger by elapsed wall-clock ms (>=1).
    """

    model_config = ConfigDict(frozen=True, extra="forbid")

    enabled: bool = True
    max_sentences: int = Field(default=3, ge=1)
    max_interval_ms: int = Field(default=500, ge=1)


class TrustClientConfig(ClientConfig):
    """HTTP client config for the Trust Layer plus output-check batching policy."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    check_output_batch: CheckOutputBatchConfig = Field(
        default_factory=CheckOutputBatchConfig
    )


class OtelConfig(BaseModel):
    """OTel SDK exporter and sampling configuration."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    collector_endpoint: str = "http://localhost:4317"
    sample_rate: float = Field(default=1.0, ge=0.0, le=1.0)
    export_interval_ms: int = Field(default=5000, gt=0)


class ObservabilityConfig(BaseModel):
    """Observability settings — OTel plus domain identifier."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    domain: str = "unknown"
    otel: OtelConfig = Field(default_factory=OtelConfig)


# ---------------------------------------------------------------------------
# agent.*
# ---------------------------------------------------------------------------


class RecentToolExchangesConfig(BaseModel):
    """Caps for cross-turn tool_use/tool_result replay (issue #193).

    Controls how many prior tool exchanges are persisted into Memory Layer
    under the session-scoped ``recent_tool_exchanges`` key and replayed as
    real ``tool_use``/``tool_result`` message pairs at the start of the
    next turn's streaming LLM call. Keeping the LLM aware of prior tool
    results avoids redundant re-invocation of the same tool with identical
    parameters across turns.
    """

    model_config = ConfigDict(frozen=True, extra="forbid")

    max_items: int = Field(default=3, ge=0)
    max_chars: int = Field(default=4000, ge=0)


class CurrentQuestionConfig(BaseModel):
    """Guardrails on the per-session ``current_question`` memory field (#207).

    The orchestrator persists every turn's bot response under ``current_question``
    so the next turn can show the LLM the previous prompt context. Pre-#200
    turn pile-ups occasionally fed concatenated multi-turn responses into this
    field, which then poisoned the next turn's prompt as
    ``[Last question asked: <bot_response_1> ... <bot_response_2> ...]``.

    The cap and the concat detector are defense-in-depth: #200's cancel-and-fold
    removes the source of the concatenation, but if it ever reappears upstream
    we want to detect and trim it rather than silently let it through.
    """

    model_config = ConfigDict(frozen=True, extra="forbid")

    max_chars: int = Field(default=500, ge=1)


class TerminationShortCircuitConfig(BaseModel):
    """Skip the LLM round trip for high-confidence termination_intent (#204).

    When the user's intent is unambiguously to end the session, calling the
    LLM only to have it speak the configured ``conversation.termination_message``
    adds ~9 s of latency for no semantic benefit. Enabling this lets the
    orchestrator emit the canned termination message directly when NLU is
    confident enough, cutting the goodbye turn down to NLU + translation.
    """

    model_config = ConfigDict(frozen=True, extra="forbid")

    enabled: bool = True
    confidence_threshold: float = Field(default=0.7, ge=0.0, le=1.0)


class FeaturesConfig(BaseModel):
    """Per-deployment chat-provider feature toggles.

    None means "use the provider's intrinsic capability." A bool tightens
    the effective feature for this deployment. Cannot widen — the
    chat_provider factory rejects True against a False capability.
    """

    model_config = ConfigDict(frozen=True, extra="forbid")

    prompt_cache: bool | None = None
    streaming: bool | None = None
    image_input: bool | None = None


class AgentConfig(BaseModel):
    """Top-level LLM wrapper settings."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    primary_model: str = ""
    fallback_model: str = ""
    provider: Literal["anthropic", "openai", "ollama", "google"] = "anthropic"
    features: FeaturesConfig = Field(default_factory=FeaturesConfig)
    timeout_ms: int = Field(default=10000, gt=0)

    @field_validator("features", mode="before")
    @classmethod
    def _coerce_null_features(cls, value):
        """Treat ``features: null`` (or YAML's empty mapping) as the default.

        YAML parses an ``agent.features:`` block whose every sub-key is
        commented out as ``None`` rather than as an empty dict. Without this
        coercion startup fails with a ValidationError on a config file that
        looks correct to a domain author. The semantics are unambiguous:
        no features expressed → use the provider's intrinsic capabilities,
        which is exactly what FeaturesConfig() defaults to.
        """
        if value is None:
            return FeaturesConfig()
        return value
    retry_attempts: int = Field(default=2, ge=1)
    retry_backoff_seconds: list[float] = Field(default_factory=lambda: [0, 0.5, 1.0])
    max_tool_rounds: int = Field(default=3, ge=1)
    ask_for_consent: bool = False
    consent_prompt: str = ""
    termination_short_circuit: TerminationShortCircuitConfig = Field(
        default_factory=TerminationShortCircuitConfig
    )
    current_question: CurrentQuestionConfig = Field(
        default_factory=CurrentQuestionConfig
    )
    recent_tool_exchanges: RecentToolExchangesConfig = Field(
        default_factory=RecentToolExchangesConfig
    )


# ---------------------------------------------------------------------------
# conversation.*
# ---------------------------------------------------------------------------


class UserStateDefinition(BaseModel):
    """One user-state entry (GH-139)."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    id: str
    signals: list[str] = Field(default_factory=list)
    guidance: str = ""


class UserStateModelConfig(BaseModel):
    """User-state classifier (opt-in, GH-139)."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    enabled: bool = False
    default_state: str = ""
    states: list[UserStateDefinition] = Field(default_factory=list)


class SessionEndEvalConfig(BaseModel):
    """Opt-in session-end signalling (GH-137).

    ``fail_action`` is validated but not yet dispatched at runtime.
    """

    model_config = ConfigDict(frozen=True, extra="forbid")

    enabled: bool = False
    prompt: str = ""
    fail_action: str = "none"


class ConversationConfig(BaseModel):
    """Static response strings plus opt-in sub-blocks."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    blocked_message: str = ""
    escalation_message: str = ""
    output_blocked_message: str = ""
    unknown_intent_message: str = ""
    termination_message: str = ""
    consent_message: str = ""
    consent_decline_ack: str = ""
    unsupported_language_message: str = ""
    profile_complete_message: str = ""
    returning_user_greeting: str = ""
    user_state_model: UserStateModelConfig = Field(default_factory=UserStateModelConfig)
    session_end_eval: SessionEndEvalConfig = Field(default_factory=SessionEndEvalConfig)


# ---------------------------------------------------------------------------
# connectors.*
# ---------------------------------------------------------------------------


class InvocationSafety(BaseModel):
    """Safety constraints exposed through a connector's invocation rules.

    Lists entries the agent must never present from a tool result (e.g.
    closed or inactive jobs) or speak aloud (e.g. GPS coordinates, match
    scores). Consumed by per-subagent prompts as grounding context.
    """

    model_config = ConfigDict(frozen=True, extra="forbid")

    never_present: list[str] = Field(default_factory=list)
    never_speak: list[str] = Field(default_factory=list)


class InvocationRules(BaseModel):
    """LLM invocation contract for a connector (GH-137, GH-176)."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    call_when: str = ""
    required_before_calling: list[str] = Field(default_factory=list)
    must_not_substitute: str = ""
    on_empty: str = ""
    on_failure: str = ""
    bridge_line: str = ""
    # GH-176: optional per-connector presentation contract. Consumed by the
    # subagent prompt rather than by any adapter — these fields shape how
    # the LLM talks about the tool's results, they do not change how the
    # tool is invoked.
    exception_no_call: str = ""
    ranking_order: list[str] = Field(default_factory=list)
    presentation_limit: int | None = None
    refinement_loop_max: int | None = None
    safety: InvocationSafety = Field(default_factory=InvocationSafety)


class InputSchema(BaseModel):
    """JSON-Schema-shaped description of a connector's input.

    Passed verbatim to the Anthropic tools API. ``properties`` is an
    open map keyed by parameter name; each property dict is left
    permissive (``dict[str, Any]``) since JSON Schema is large.
    """

    model_config = ConfigDict(frozen=True, extra="forbid")

    type: str = "object"
    properties: dict[str, dict[str, Any]] = Field(default_factory=dict)
    required: list[str] = Field(default_factory=list)
    additionalProperties: bool = False


class ConnectorDef(BaseModel):
    """External-facing connector (read / write / identity)."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    name: str
    description: str = ""
    input_schema: InputSchema = Field(default_factory=InputSchema)
    invocation_rules: InvocationRules = Field(default_factory=InvocationRules)


class InternalConnectorDef(BaseModel):
    """Internal connector routed to another DPG block (e.g. knowledge_retrieval)."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    name: str
    route: str
    description: str = ""
    input_schema: InputSchema = Field(default_factory=InputSchema)
    invocation_rules: InvocationRules = Field(default_factory=InvocationRules)


class ConnectorsConfig(BaseModel):
    model_config = ConfigDict(frozen=True, extra="forbid")

    read: list[ConnectorDef] = Field(default_factory=list)
    write: list[ConnectorDef] = Field(default_factory=list)
    identity: list[ConnectorDef] = Field(default_factory=list)
    internal: list[InternalConnectorDef] = Field(default_factory=list)


# ---------------------------------------------------------------------------
# preprocessing.*
# ---------------------------------------------------------------------------


class LanguageNormalisationConfig(BaseModel):
    """LLM-native language normalisation block."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    # GH-313: when False the leading LLM call is skipped; the main LLM mirrors
    # the user's language via a directive in build_system_prompt(). Defaults to
    # True for backward compatibility; KKB sets False.
    enabled: bool = True

    # Per-helper provider override (#287 follow-up). When set, build_chat_provider
    # uses this provider for the language-norm helper instead of inheriting
    # agent.provider. Lets a deployment run primary chat on OpenAI while
    # keeping language norm on Anthropic (or vice versa). None → inherit.
    provider: Literal["anthropic", "openai", "ollama", "google"] | None = None
    model: str = ""
    default_language: str = ""
    supported_languages: list[str] = Field(default_factory=list)
    min_detection_tokens: int = Field(default=3, gt=0)
    transliteration: bool = True
    code_switching: bool = True


class NLUProcessorConfig(BaseModel):
    """NLU intent + entity + sentiment classifier."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    # Per-helper provider override — see LanguageNormalisationConfig.provider.
    provider: Literal["anthropic", "openai", "ollama", "google"] | None = None
    model: str = ""
    confidence_threshold: float = Field(default=0.5, ge=0.0, le=1.0)
    user_state_confidence_threshold: float = Field(default=0.4, ge=0.0, le=1.0)
    domain_instruction: str = ""
    intents: list[str] = Field(default_factory=list)
    entities: list[str] = Field(default_factory=list)
    sentiment_classes: list[str] = Field(
        default_factory=lambda: ["neutral", "positive", "distressed", "frustrated"]
    )
    signal_intents: dict[str, str] = Field(default_factory=dict)
    # GH-218: opt-in INFO log with the full parsed NLU response JSON and the
    # final composed user message. Off by default because the values can
    # carry PII (entity values, message text). Turn on for triage windows.
    log_raw_response: bool = False
    log_raw_response_max_chars: int = Field(default=2000, ge=0)


class PreprocessingConfig(BaseModel):
    model_config = ConfigDict(frozen=True, extra="forbid")

    language_normalisation: LanguageNormalisationConfig = Field(
        default_factory=LanguageNormalisationConfig
    )
    nlu_processor: NLUProcessorConfig = Field(default_factory=NLUProcessorConfig)


# ---------------------------------------------------------------------------
# hitl
# ---------------------------------------------------------------------------


class HitlResponseConfig(BaseModel):
    model_config = ConfigDict(frozen=True, extra="forbid")

    response_message: str = ""


# ---------------------------------------------------------------------------
# agent_workflow.*
# ---------------------------------------------------------------------------


class RoutingCondition(BaseModel):
    """Single predicate evaluated against a session field."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    field: str
    operator: RoutingOperator
    value: Any = None


class RoutingRule(BaseModel):
    """Routing decision from a subagent."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    intent: str
    next_subagent_id: str
    condition: Optional[RoutingCondition] = None
    conditions: list[RoutingCondition] = Field(default_factory=list)
    session_writes: dict[str, Any] = Field(default_factory=dict)


class SubAgent(BaseModel):
    """One subagent node in the workflow graph."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    id: str
    name: str = ""
    description: str = ""
    is_start: bool = False
    is_terminal: bool = False
    opening_phrase: str = ""
    special_handler: Optional[SpecialHandler] = None
    valid_intents: list[str] = Field(default_factory=list)
    tools: list[str] = Field(default_factory=list)
    system_prompt: str = ""
    output_format: Optional[dict[str, Any]] = None
    routing: list[RoutingRule] = Field(default_factory=list)


class AgentWorkflowConfig(BaseModel):
    """Multi-subagent workflow graph."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    workflow_id: str = ""
    version: str = "1.0.0"
    agent_system_prompt: str = ""
    global_intents: list[str] = Field(default_factory=list)
    global_routing: list[RoutingRule] = Field(default_factory=list)
    default_fallback_subagent_id: str = ""
    global_tools: list[str] = Field(default_factory=list)
    subagents: list[SubAgent] = Field(default_factory=list)


# ---------------------------------------------------------------------------
# channels.* (GH-137) — chat channel removed as unused
# ---------------------------------------------------------------------------


class TtsRulesConfig(BaseModel):
    """TTS formatting rules for a voice channel."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    numbers: str = ""
    money: str = ""
    dates: str = ""
    time: str = ""
    phone: str = ""
    abbreviations: str = ""
    output_script: str = ""
    english_loanwords: str = ""
    email: str = ""
    named_entities: str = ""


class SemanticGateConfig(BaseModel):
    model_config = ConfigDict(frozen=True, extra="forbid")

    enabled: bool = False
    confidence_threshold: float = Field(default=0.75, ge=0.0, le=1.0)


class SilenceTriggerConfig(BaseModel):
    model_config = ConfigDict(frozen=True, extra="forbid")

    silence_ms: int = Field(default=0, ge=0)


class MaxWaitCeilingConfig(BaseModel):
    model_config = ConfigDict(frozen=True, extra="forbid")

    max_wait_ms: int = Field(default=0, ge=0)


class TurnAssemblerConfig(BaseModel):
    """Turn-assembler policy stack."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    semantic_gate: SemanticGateConfig = Field(default_factory=SemanticGateConfig)
    silence_trigger: SilenceTriggerConfig = Field(default_factory=SilenceTriggerConfig)
    max_wait_ceiling: MaxWaitCeilingConfig = Field(default_factory=MaxWaitCeilingConfig)


class ChannelConfig(BaseModel):
    """Per-channel LLM-facing configuration (GH-137).

    ``max_tokens`` (GH-194) caps the LLM response length on this channel.
    When ``None`` the wrapper falls back to its built-in default (4096).
    Voice channels typically set a tight cap (~200) so the user never
    waits through long monologues.
    """

    model_config = ConfigDict(frozen=True, extra="forbid")

    system_prompt_suffix: str = ""
    tts_rules: Optional[TtsRulesConfig] = None
    terminal_word: Optional[str] = None
    max_tokens: Optional[int] = Field(default=None, gt=0)
    turn_assembler: TurnAssemblerConfig = Field(default_factory=TurnAssemblerConfig)
    # GH-242: filler_threshold_ms and filler_phrase used to live here, but
    # they are read by the reach_layer voice service (not agent_core), so
    # declaring them in agent_core's config block meant they never reached
    # the voice service at runtime. Moved to
    # reach_layer/base/schema/config.py: VoiceChannelConfig.


class ChannelsConfig(BaseModel):
    """Per-channel config block. ``chat`` removed as unused in this PR."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    voice: ChannelConfig = Field(default_factory=ChannelConfig)
    web: ChannelConfig = Field(default_factory=ChannelConfig)
    cli: ChannelConfig = Field(default_factory=ChannelConfig)


# ---------------------------------------------------------------------------
# reach_layer — top-level default turn-assembler (inherited by channels)
# ---------------------------------------------------------------------------


class ReachLayerDefaultsConfig(BaseModel):
    """Default turn-assembler policy stack consumed by Agent Core.

    Lives at the top level intentionally — Agent Core reads these as
    fallbacks when a channel does not declare its own turn_assembler
    block under ``channels.<name>``.
    """

    model_config = ConfigDict(frozen=True, extra="forbid")

    turn_assembler: TurnAssemblerConfig = Field(default_factory=TurnAssemblerConfig)


# ---------------------------------------------------------------------------
# Top-level merged config
# ---------------------------------------------------------------------------


class MergedConfig(BaseModel):
    """Strict schema for the fully-merged agent_core config."""

    model_config = ConfigDict(frozen=True, extra="forbid")

    server: ServerConfig = Field(default_factory=ServerConfig)

    agent: AgentConfig = Field(default_factory=AgentConfig)
    conversation: ConversationConfig = Field(default_factory=ConversationConfig)
    connectors: ConnectorsConfig = Field(default_factory=ConnectorsConfig)
    preprocessing: PreprocessingConfig = Field(default_factory=PreprocessingConfig)
    entity_to_profile_field: dict[str, str] = Field(default_factory=dict)
    hitl: HitlResponseConfig = Field(default_factory=HitlResponseConfig)
    agent_workflow: AgentWorkflowConfig = Field(default_factory=AgentWorkflowConfig)
    channels: ChannelsConfig = Field(default_factory=ChannelsConfig)
    reach_layer: ReachLayerDefaultsConfig = Field(default_factory=ReachLayerDefaultsConfig)

    # Inter-service HTTP clients
    ke_client: ClientConfig = Field(
        default_factory=lambda: ClientConfig(
            endpoint="http://knowledge_engine:8001/retrieve"
        )
    )
    memory_client: ClientConfig = Field(
        default_factory=lambda: ClientConfig(endpoint="http://memory_layer:8002")
    )
    trust_client: TrustClientConfig = Field(
        default_factory=lambda: TrustClientConfig(endpoint="http://trust_layer:8003")
    )
    learning_client: ClientConfig = Field(
        default_factory=lambda: ClientConfig(endpoint="http://observability_layer:8004")
    )
    action_gateway_client: ClientConfig = Field(
        default_factory=lambda: ClientConfig(endpoint="http://action_gateway:9999")
    )

    observability: ObservabilityConfig = Field(default_factory=ObservabilityConfig)

    @classmethod
    def validate_full(cls, config: dict) -> "MergedConfig":
        """Validate the full merged config dict against the strict schema.

        Args:
            config: Merged dict (dpg defaults + domain overrides).

        Returns:
            Validated MergedConfig instance.

        Raises:
            pydantic.ValidationError: If the config contains unknown keys,
                wrong value types, or values outside the allowed ranges at
                any nesting level.
            TypeError: If config is None.
        """
        if config is None:
            raise TypeError("config must be a dict, got None")
        return cls.model_validate(config)

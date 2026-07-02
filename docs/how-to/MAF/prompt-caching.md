# History Management and Token Optimization

How conversation history grows in TemporalAgents, how the framework manages it across turns and continue-as-new boundaries, and strategies for controlling token costs.

---

## Table of Contents

1. [Overview](#overview)
2. [How History Grows](#how-history-grows)
3. [History Serialization Format](#history-serialization-format)
4. [Continue-as-New: Automatic History Transfer](#continue-as-new-automatic-history-transfer)
5. [Token Usage Monitoring](#token-usage-monitoring)
6. [Strategies for Reducing Token Costs](#strategies-for-reducing-token-costs)
7. [External Memory with AIContextProvider](#external-memory-with-aicontextprovider)
8. [StateBag Persistence](#statebag-persistence)

---

## Overview

Every agent session in TemporalAgents maintains a conversation history — the full sequence of user messages, assistant responses, tool calls, and tool results. This history is:

1. **Stored in workflow state** (`AgentWorkflow._history`) as a `List<DurableSessionEntry>` populated with `AgentSessionRequest` / `AgentSessionResponse` instances (MAF subclasses of the shared `DurableSessionRequest` / `DurableSessionResponse` types in `TemporalCommunity.Extensions.AI`). Each entry's `Messages` is `IReadOnlyList<ChatMessage>` (MEAI type, stored directly).
2. **Flattened into `AgentStepInput.AccumulatedMessages`** at the start of every turn by `AgentWorkflow.ExecuteDurableAgentTurnAsync`, then re-sent on each step of the per-LLM-call durable loop
3. **Sent to the LLM** by `AgentActivities.RunDurableAgentStepAsync` via `IChatClient.GetStreamingResponseAsync`
4. **Carried across continue-as-new boundaries** via `AgentWorkflowInput.CarriedHistory`

This means that by default, the LLM sees the **complete conversation** on every turn. For long-running sessions, this can lead to significant token costs and eventually hit context window limits.

---

## How History Grows

Each turn adds two entries to the history:

```
Turn 1:  [Request₁]  →  [Response₁]                    = 2 entries
Turn 2:  [Request₁] [Response₁] [Request₂]  →  [Response₂]  = 4 entries
Turn 3:  ... = 6 entries
Turn N:  ... = 2N entries
```

The flattened message list is serialized into each `RunDurableAgentStep` activity input as `AgentStepInput.AccumulatedMessages`, so the Temporal event payload grows with each turn (one entry per LLM step within the turn). The full history is rebuilt at the start of each turn and re-sent on every step:

```csharp
// Inside AgentWorkflow.ExecuteDurableAgentTurnAsync, before the per-step loop:
var accumulated = FlattenHistoryMessages();   // _history → flat List<ChatMessage>

// On each iteration:
var stepInput = new AgentStepInput
{
    AgentName = _input.AgentName,
    Request = runRequest,
    AccumulatedMessages = accumulated,        // re-sent every step
    SerializedStateBag = _currentStateBag,
    IsFirstStep = (iteration == 0),
};
```

`entry.Messages` is `IReadOnlyList<ChatMessage>` (MEAI types stored directly), so no per-message conversion step is needed — each `msg` is already a `ChatMessage`.

**Token cost grows quadratically** with turn count: turn N sends all N previous exchanges plus the new message. A 20-turn conversation sends ~40 messages to the LLM on the final turn.

---

## History Serialization Format

History entries use a polymorphic JSON format with a `$type` discriminator at the entry layer. The MAF-specific subclasses use the discriminators `agent_request` / `agent_response`; the AI library's own concrete types (in mixed-library scenarios) use `ai_request` / `ai_response`. Within each entry's `messages`, individual `AIContent` items carry MEAI's own `$type` discriminator (e.g., `text`, `functionCall`, `functionResult`) emitted by `AIJsonUtilities.DefaultOptions`:

```json
[
  {
    "$type": "agent_request",
    "correlationId": "abc123",
    "createdAt": "2026-04-30T10:00:00Z",
    "messages": [
      {
        "role": "user",
        "contents": [{ "$type": "text", "text": "What is the weather?" }]
      }
    ]
  },
  {
    "$type": "agent_response",
    "correlationId": "abc123",
    "createdAt": "2026-04-30T10:00:01Z",
    "messages": [
      {
        "role": "assistant",
        "contents": [{ "$type": "text", "text": "The weather is sunny." }]
      }
    ],
    "usage": {
      "inputTokenCount": 42,
      "outputTokenCount": 8,
      "totalTokenCount": 50
    }
  }
]
```

The serialization captures all MEAI `AIContent` subtypes — `TextContent`, `FunctionCallContent`, `FunctionResultContent`, `DataContent`, `ErrorContent`, `UsageContent`, `TextReasoningContent`, `UriContent`, and more — directly via `AIJsonUtilities.DefaultOptions`'s polymorphic discriminator. New MEAI content types are picked up automatically; no per-type wrapper is needed. Token usage is preserved per-response for monitoring.

---

## Continue-as-New: Automatic History Transfer

Temporal workflows accumulate event history over time. When the history gets too large, `AgentWorkflow` transfers the conversation to a fresh workflow run via continue-as-new:

```csharp
// Inside AgentWorkflow.RunAsync
if (Workflow.ContinueAsNewSuggested && !_shutdownRequested)
{
    var carriedHistory = _history.ToList();
    var carriedStateBag = _currentStateBag;

    throw Workflow.CreateContinueAsNewException(
        (AgentWorkflow wf) => wf.RunAsync(new AgentWorkflowInput
        {
            AgentName = input.AgentName,
            CarriedHistory = carriedHistory,
            CarriedStateBag = carriedStateBag,
            // ... other config propagated
        }));
}
```

**What survives continue-as-new:**
- Full conversation history (`CarriedHistory`)
- StateBag state (`CarriedStateBag`) — including AIContextProvider state like Mem0 thread IDs
- All configuration: TTL, activity timeouts, approval timeout

**What resets:**
- Temporal event history (the Temporal-level history, not conversation history)
- Run ID (changes to a new value)
- Workflow timers

The conversation is seamless from the user's perspective — the workflow ID stays the same, and the next `RunAsync` call routes to the new run automatically.

---

## Token Usage Monitoring

Token counts are captured at two levels:

### Per-Turn: OTel Span Attributes

The `agent.turn` span includes token metrics from the LLM response:

```
agent.turn
  agent.input_tokens  = 1542
  agent.output_tokens = 87
  agent.total_tokens  = 1629
```

These are only set when the underlying LLM provider reports usage data.

### Per-Turn: Structured Logs

`AgentActivities` logs token counts on each turn:

```
Agent activity completed for 'WeatherAgent' (workflow: ta-weatheragent-abc123).
  Input tokens: 1542, Output tokens: 87, Total tokens: 1629
```

### Per-Response: History State

Token usage is stored on each response entry as `Microsoft.Extensions.AI.UsageDetails` (the MEAI type, used directly — no wrapper), making it available for retrospective analysis via the `GetHistory` workflow query. The query returns `IReadOnlyList<DurableSessionEntry>`; pattern-match on `DurableSessionResponse` (or its MAF subclass `AgentSessionResponse`) to access typed `Usage`:

```csharp
var handle = client.GetWorkflowHandle<AgentWorkflow>(workflowId);
var history = await handle.QueryAsync(wf => wf.GetHistory());

foreach (var entry in history.OfType<DurableSessionResponse>())
{
    Console.WriteLine($"Turn: {entry.Usage?.TotalTokenCount} tokens");
}
```

The `OfType<DurableSessionResponse>()` filter matches both `DurableSessionResponse` and the MAF-specific `AgentSessionResponse` subclass (inheritance-based). Cast individual entries to `AgentSessionRequest` to access the MAF-only fields (`OrchestrationId`, `ResponseType`, `ResponseSchema`).

### Aggregate: Search Attributes

When `EnableSearchAttributes = true`, the `TurnCount` search attribute lets you find high-activity sessions in the Temporal UI:

```
AgentName = "ResearchAgent" AND TurnCount > 20
```

---

## Strategies for Reducing Token Costs

### 1. Use Short-Lived Sessions

Set a low `timeToLive` so sessions expire before history grows too large:

```csharp
opts.AddDurableAgent("MyAgent", agent =>
{
    agent.ChatClient = sp => sp.GetRequiredService<IChatClient>();
    agent.TimeToLive = TimeSpan.FromHours(1);
});
```

After TTL expires, the next message starts a fresh session with empty history.

### 2. Summarize History Before Sending

Create a summarization step inside a workflow that condenses long histories before passing to a specialist agent:

```csharp
[WorkflowRun]
public async Task<string> RunAsync(string question)
{
    var researcher = GetAgent("Researcher");
    var session = await researcher.CreateSessionAsync();

    // Multiple turns build up history on the researcher agent
    for (int i = 0; i < 5; i++)
    {
        await researcher.RunAsync($"Research step {i}", session);
    }

    // Summarize the researcher's findings with a fresh agent (no history baggage)
    var summarizer = GetAgent("Summarizer");
    var sumSession = await summarizer.CreateSessionAsync();
    var summary = await summarizer.RunAsync(
        $"Summarize these findings concisely: {lastResponse.Text}",
        sumSession);

    return summary.Text ?? string.Empty;
}
```

The summarizer sees only the final output, not the full 5-turn research history.

### 3. Use External Memory Instead of Full History

`AIContextProvider` implementations (like Mem0) store memories externally and inject only relevant context on each turn. This decouples "what the agent remembers" from "the full conversation transcript":

```csharp
opts.AddDurableAgent("MemoryAgent", agent =>
{
    agent.Instructions = "You are a helpful assistant with long-term memory.";
    agent.ChatClient   = sp => sp.GetRequiredService<IChatClient>();
    agent.AddContextProvider(sp => new Mem0ContextProvider(
        sp.GetRequiredService<Mem0Client>(),
        userId: "user-001"));
});
```

The provider injects a small set of relevant memories instead of the full history, keeping token counts low even across many turns.

### 4. Use One-Shot Sessions for Independent Tasks

For tasks that don't need conversational context, use a fresh session per request:

```csharp
// Each call starts fresh — no history accumulation
var session = new TemporalAgentSessionId("AnalystAgent", Guid.NewGuid().ToString("N"));
var response = await client.SendAsync(session, new RunRequest("Analyze this data: ..."));
```

Or use `AgentJobWorkflow` via scheduling, which always starts with empty history.

> **Note:** The `RunAgentAsync(string agentName, string message)` convenience overload is deprecated. Use `SendAsync(TemporalAgentSessionId, RunRequest)` directly.

### 5b. Cap History at a Fixed Size with MaxEntryCount

`TemporalAgentsOptions.DefaultMaxEntryCount` sets a hard cap on the number of history entries kept in the workflow. When the cap is reached, the workflow triggers continue-as-new, discarding the oldest entries:

```csharp
builder.Services
    .AddHostedTemporalWorker("localhost:7233", "default", "agents")
    .AddTemporalAgents(opts =>
    {
        opts.AddDurableAgent("Agent", a => a.ChatClient = sp => sp.GetRequiredService<IChatClient>());
        opts.DefaultMaxEntryCount = 50;  // keep at most 50 entries across continue-as-new
    });
```

Pair with a `HistoryReducer` to control which entries are retained at the boundary. The reducer signature is now `Func<IList<DurableSessionEntry>, IList<DurableSessionEntry>>?` — entry-shaped on both libraries, matching the unified entry-layer wire format:

```csharp
opts.DefaultMaxEntryCount = 50;
opts.DefaultHistoryReducer = entries =>
{
    // Keep the most recent 30 entries; drop older ones
    return entries.TakeLast(30).ToList();
};
```

`HistoryReducer` is called with the full history immediately before continue-as-new. The returned subset becomes the initial history for the new run. A `null` reducer (the default) retains all entries up to `MaxEntryCount`, dropping the oldest. The reducer must be synchronous and deterministic — it runs in workflow context.

#### `HistoryReducer` × `UseCompaction` precedence

`UseCompaction` (Step 5+6, in-session compaction) and `HistoryReducer` (continue-as-new-time reduction) compose; they target different boundaries.

| Layer | When | Operates on | Purpose |
|---|---|---|---|
| `UseCompaction` | After every final-step turn that crosses the trigger threshold | Audit canonical view (`applyCompaction: false`) | Bound in-session inference cost; produces `CompactionMarkerEntry` |
| `HistoryReducer` | At continue-as-new only | Projected view (`applyCompaction: true`) | Bound workflow event-history size at the CAN boundary |

Per the Q5α design rule, when both are configured the reducer operates on the **post-compact projection** — so it reduces the view the LLM has been seeing rather than the raw entries. The `ReduceHistoryInStore` activity loads with `applyCompaction: true` automatically; no caller action needed.

See [`compaction.md`](./compaction.md) for the full compaction story.

### 5. Use ResponseFormat to Get Structured Output

Structured output (JSON) is typically more token-efficient than natural language:

```csharp
var report = await agent.RunAsync<WeatherReport>(messages, session);
```

The LLM generates compact JSON instead of verbose prose, reducing output tokens.

### 6. Filter Tools per Request

Disable unnecessary tools to reduce the system prompt size (each tool definition adds tokens):

```csharp
var options = new TemporalAgentRunOptions
{
    EnableToolNames = ["get_weather"],  // only this tool is available
    // EnableToolCalls = false          // or disable all tools
};
```

---

## External Memory with AIContextProvider

For a detailed explanation of how `AIContextProvider` and `AgentSessionStateBag` work, see [Session StateBag & Context Providers](../architecture/MAF/session-statebag-and-context-providers.md).

The key insight for token optimization: providers run inside `AgentActivities.RunDurableAgentStepAsync` (the activity, not the workflow), so they can make external I/O calls safely. The provider decides what context to inject — it could be a few relevant memories from a vector database rather than the entire conversation history.

---

## StateBag Persistence

`AgentSessionStateBag` carries provider state (like Mem0 thread IDs) across turns without serializing the provider's full data store:

```
Turn 1: Activity starts → empty StateBag
        Provider writes: bag["mem0_thread_id"] = "t-abc"
        Activity ends → bag serialized → workflow stores it

Turn 2: Activity starts → bag restored from workflow state
        Provider reads: bag["mem0_thread_id"] → "t-abc" (skips re-init)
        Activity ends → bag re-serialized

Continue-as-New:
        carriedStateBag = _currentStateBag  → new workflow run
        Bag restored seamlessly in the next turn
```

**Optimization detail:** Empty bags serialize to `null` (checked via `StateBag.Count == 0`), so sessions without providers incur zero serialization overhead.

---

## References

- `src/TemporalCommunity.Extensions.Agents/Workflows/AgentWorkflow.cs` — history storage and continue-as-new
- `src/TemporalCommunity.Extensions.Agents/Workflows/AgentActivities.cs` — history rebuild and token logging
- `src/TemporalCommunity.Extensions.Agents/State/` — serialization types for conversation history
- [Session StateBag & Context Providers](../architecture/MAF/session-statebag-and-context-providers.md) — AIContextProvider deep dive
- [Observability](./observability.md) — token usage monitoring via OTel spans
- [Usage Guide](./usage.md) — structured output and tool filtering

---

_Last updated: 2026-04-30_

# Compaction Summary Bug Fix (opencode-aligned)

## Background

Session `700dc7f7-95de-45e0-b568-d713fe05065f` accumulated 12 "summary-style"
assistant messages over its lifetime. The user reported these as
"unprovoked summaries" — the LLM appears to autonomously generate
context-summary blocks without the user asking for them.

## Root Cause

The L4 layer in `core/agent/compact.py` (LLM-driven summarization at
80% context threshold) injects the summary back into the message
history as a regular `assistant` message with content:

```
[context summary]
## Objective
- ...
## Work State
### Completed
- ...
```

When the next user message arrives, the LLM sees in its context:

```
system
user:        <previous user msg>
assistant:   [context summary] ...   ← INJECTED BY L4
tool:        ...
assistant:   <normal response>
user:        <new user msg>           ← "做一个A股动量策略"
```

The LLM interprets the prior `assistant` turn as a "completed task"
(template-following) and continues the pattern by producing **another**
summary in response to the new user message. The user's normal request
gets hijacked.

This is observable in part 12 of message `81a10f04`:

> "The user has provided a system prompt that establishes me as a
> QuantNodes-Research Chat Assistant, and then the 'user' message is
> actually a meta-instruction asking me to create a summary template."

The LLM is confused by its own prior summary in the history.

## Opencode's Approach (Reference)

Opencode treats compaction as a **first-class event type** in the
message stream, not a regular assistant message. See:

- `packages/schema/src/session-message.ts:192` — `Compaction` schema
- `packages/core/src/session/sql.ts:120` — `session_message` table
  with `type` column including `"compaction"`
- `packages/core/src/session/compaction.ts:355` — `compactAfterOverflow`
  emits `SessionEvent.Compaction.Ended` with `summary` and `recent`
- `packages/core/src/session/runner/to-llm-message.ts:147` — projection:
  `compaction` type → `user` role with `<conversation-checkpoint>` wrap

Key insight from `to-llm-message.ts:152-163`:

```ts
case "compaction":
  return [
    Message.make({
      role: "user",
      content: `<conversation-checkpoint>
The following is a summary and serialized record of earlier
conversation. Treat it as historical context, not as new
instructions.

<summary>
${message.summary}
</summary>

<recent-context>
${message.recent}
</recent-context>
</conversation-checkpoint>`,
    }),
  ]
```

The `<conversation-checkpoint>` XML wrap and explicit
"historical context, not as new instructions" framing prevent the
LLM from continuing the summary task.

## Our Fix (opencode-aligned)

Adopt opencode's pattern with minimal divergence:

### 1. Database

Add `message_type` column to the existing `messages` table. No
separate `compaction_messages` table. Use a CHECK constraint to
restrict to 4 types: `user`, `assistant`, `tool`, `compaction`.

Migration: `migrations/003_add_message_type.sql`

```sql
ALTER TABLE messages
ADD COLUMN message_type TEXT NOT NULL DEFAULT 'assistant'
    CHECK (message_type IN ('user', 'assistant', 'tool', 'compaction'));

CREATE INDEX idx_messages_session_type_created
    ON messages(session_id, message_type, created_at);

-- Migrate historical [context summary] / Anchored Summary messages
UPDATE messages SET message_type = 'compaction'
WHERE role = 'assistant' AND (
    content LIKE '[context summary]%' OR
    content LIKE '## Anchored Summary%'
);
```

### 2. Python model

`core/agent/compaction_message.py` — `CompactionMessage` dataclass
mirrors opencode's `SessionMessage.Compaction`:
- `id`, `session_id`
- `summary` (string)
- `recent` (serialized recent messages, string)
- `reason` ("auto" | "manual")
- `metadata` (dict)

Stored in the same `messages` table with:
- `role = "assistant"` (DB constraint compat)
- `message_type = "compaction"`
- `content = summary` (denormalized for query)
- `parts_json = [{type: "compaction", summary, recent, reason}]`

### 3. LLM projection

`core/agent/to_llm_message.py` — single source of truth for
"what the LLM sees".

```python
def project_to_llm_message(db_message: dict) -> dict | None:
    msg_type = db_message.get("message_type") or _infer_type(db_message)
    if msg_type == "compaction":
        comp = CompactionMessage.from_db_row(db_message)
        return comp.to_llm_message()  # user role + checkpoint wrap
    elif msg_type == "user":
        return {"role": "user", "content": ...}
    elif msg_type == "tool":
        return {"role": "tool", ...}
    elif msg_type == "assistant":
        return {"role": "assistant", ...}
    return None
```

The key fix: `compaction` is projected as **`user` role** with the
`<conversation-checkpoint>` wrap. The LLM sees it as "user-provided
context" not "previous assistant turn".

### 4. Compact layer

`core/agent/compact.py` no longer injects the summary as an inline
`assistant` message. Instead:
- Generate summary text via LLM (same as before)
- Persist as a `compaction`-typed message via `MessageStore.append_message`
- Return the head/recent split WITHOUT the summary inline

The next LLM call will load the compaction via `to_llm_message()` and
project it correctly.

### 5. Backward compat

`_infer_type()` provides double-safety:
- New code reads `message_type` column
- Old data without `message_type` infers from `content` prefix

This means even if the migration doesn't run, the new code still
correctly identifies compactions and applies the LLM fix.

## Files Changed

| File | Type | Purpose |
|------|------|---------|
| `migrations/003_add_message_type.sql` | NEW | Schema migration |
| `src/strategy_research/core/agent/compaction_message.py` | NEW | `CompactionMessage` dataclass + DB I/O |
| `src/strategy_research/core/agent/to_llm_message.py` | NEW | Unified LLM projection |
| `src/strategy_research/core/agent/compact.py` | MOD | Persist compaction, no inline injection |
| `src/strategy_research/core/agent/loop.py` | MOD | Use `to_llm_message`, drop `[context summary]` matching |
| `src/strategy_research/api/session/service.py` | MOD | Filter by `message_type`, compat for old format |
| `src/strategy_research/api/session/store.py` | MOD | Support `message_type` parameter |
| `src/strategy_research/cli/tui/app.py` | MOD | Skip rendering `compaction` messages |
| `tests/test_compaction_message.py` | NEW | Dataclass + DB I/O tests |
| `tests/test_to_llm_message.py` | NEW | Projection tests (incl. regression) |
| `tests/test_compact.py` | MOD | Update existing tests for new format |

## Why This Fixes the Bug

**Before**: compaction → assistant message → LLM treats as previous
turn → continues pattern → another summary

**After**: compaction → user message with explicit "historical context,
not new instructions" framing → LLM processes new user message
normally

The XML wrap + user role + explicit instruction is the proven
opencode approach that prevents the LLM from confusing summary tasks
with normal conversation.

## Verification Plan

1. Apply migration on test DB
2. Load existing session 700dc7f7 — verify compactions are filtered
3. Start new chat session, force L4 compaction (large context)
4. Send normal user message after compaction
5. Verify LLM does NOT produce another summary
6. Run all 132+ existing tests + new ones (no regressions)

## Out of Scope (Future PRs)

- Compaction UI in settings/debug panel
- Compaction cost tracking (input_tokens, output_tokens per event)
- Compaction rate-limiting (max N compactions per session)
- Manual `/compact` command UI improvements

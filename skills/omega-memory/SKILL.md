---
name: omega-memory
description: "Persistent memory for AI coding agents. Teaches agents how to use OMEGA's MCP tools for long-context retrieval, full memory hydration, project context packs, storing decisions, and resuming tasks across sessions."
license: Apache-2.0
compatibility: "Python 3.11+, Claude Code, Cursor, Windsurf, Zed"
metadata:
  category: memory
  pypi: omega-memory
  github: omega-memory/omega-memory
---

# OMEGA Memory

Persistent memory for AI coding agents. OMEGA gives your agent a knowledge graph it can query, learn from, and coordinate through across sessions.

This skill teaches you how to use OMEGA's MCP tools effectively.

## Setup

```bash
pip3 install omega-memory[server]
omega setup        # auto-configures your editor + downloads embedding model
omega doctor       # verify everything works
```

Works with Claude Code, Cursor, Windsurf, Zed, and any MCP client.

## MCP Tool Discovery

OMEGA exposes its tools through MCP `tools/list`: the client receives tool
names, descriptions, and JSON input schemas, then validates calls through
`tools/call`. Some clients show every schema directly. In condensed mode,
OMEGA intentionally exposes only high-frequency tools plus `omega_tools` and
`omega_call`; use those two meta-tools to discover and call the rest.

Discovery pattern in condensed mode:

```text
omega_tools(category="query")
omega_tools(tool="omega_recall")
omega_call(tool="omega_recall", args={"query": "...", "profile": "planning"})
```

## Long-Context Retrieval Workflow

Use this order when coding in a large repo or resuming a long task:

1. `omega_welcome(project=...)` for the session briefing.
2. `omega_protocol(project=..., section="full")` for operating rules.
3. `omega_context(project=..., mode="handoff")` for project-scoped recovery.
4. `omega_recall(query=..., profile=..., project=..., budget_chars=...)` when
   you need enough full memory content to act.
5. `omega_query(format="json", content_mode="preview"|"full")` when you need
   structured search results for inspection or follow-up logic.
6. `omega_memory(action="get", memory_id="mem-...")` when search gives you a
   stable ID and you need the full record.
7. `omega_store(...)` or `omega_checkpoint(...)` after meaningful state changes.

## Core Tools

### Storing Memories

**`omega_store(content, event_type, metadata?, entity_id?)`**

Store decisions, lessons, and context that should persist across sessions.

| Event Type | When to Use | TTL |
|------------|------------|-----|
| `decision` | Architectural choices, technology selections | 90 days |
| `lesson_learned` | Debugging insights, patterns that worked/failed | 90 days |
| `user_preference` | Code style, workflow preferences, tool choices | Permanent |
| `error_pattern` | Recurring errors and their fixes | 30 days |
| `task_completion` | Completed work with outcomes | 14 days |
| `checkpoint` | Mid-task state for resumption | 7 days |

```
omega_store("Switched from REST to GraphQL for the dashboard API - reduces N+1 queries", "decision")
omega_store("User prefers early returns, max 2 levels of nesting", "user_preference")
omega_store("pytest fixtures with db cleanup must use function scope, not session scope", "lesson_learned")
```

**Don't store:** Raw code output, tool results, transient status updates, anything shorter than a sentence.

### Querying Memories

**`omega_query(query, mode?, limit?, entity_id?, format?, content_mode?)`**

Search memories by meaning, not just keywords. Uses hybrid retrieval: vector similarity + full-text search + cross-encoder reranking.

| Mode | When to Use |
|------|------------|
| `semantic` (default) | Find memories by meaning — "how did we handle auth?" |
| `phrase` | Exact substring match — find a specific term or identifier |
| `timeline` | Recent memories grouped by day — "what happened this week?" |
| `browse` | List by type, session, or recency — explore what's stored |

```
omega_query("database migration strategy")
omega_query("what decisions were made about the API", mode="timeline", days=7)
omega_query("pytest", mode="phrase")
omega_query(mode="browse", browse_by="type", event_type="lesson_learned", offset=0)
omega_query("pre-PR checklist", format="json", content_mode="full", budget_chars=12000)
```

Use `content_mode="preview"` for cheap inspection, `content_mode="full"` only
when you need full bodies, and `format="json"` when the caller needs stable
IDs, metadata, truncation state, and follow-up targets.

### Prompt-Ready Recall

**`omega_recall(query, profile?, project?, budget_chars?, expand_related?)`**

Search, hydrate, deduplicate, and pack relevant memories into one bounded
context block. Use it when a normal query preview is not enough to resume or
make a coding decision.

| Profile | When to Use |
|---------|-------------|
| `general` | Default broad recall |
| `debug` | Errors, CI failures, fixes, exact phrase fallback |
| `planning` | Decisions, constraints, task completions, project setup |
| `handoff` | Checkpoints, completions, recent continuity state |
| `review` | Lessons, decisions, contradictions, stale markers |
| `implementation` | Code patterns, file context, lessons, error patterns |

```text
omega_recall("sentinel-core pre-PR checklist", profile="handoff", project="/home/akalanka/sentinel-core")
omega_recall("pytest sqlite lock failure", profile="debug", budget_chars=12000)
omega_recall("restore workflow decisions", profile="implementation", expand_related=true, max_related=3)
```

Prefer `omega_recall` over chaining several broad queries when context is long.
It returns the searches used, selected IDs, omitted IDs, and truncation status.
When `expand_related=true`, related memories are ordered deterministically by
nearest hop, strongest edge weight, edge-type priority, newest edge timestamp,
then stable memory ID.

### Direct Memory Hydration

**`omega_memory(action="get", memory_id?, memory_ids?, include_edges?)`**

Fetch full memories by stable ID. Use this after `omega_query`, `omega_recall`,
or `omega_context` returns an ID that needs exact inspection.

```text
omega_memory(action="get", memory_id="mem-abc123", format="json")
omega_memory(action="get", memory_ids=["mem-a", "mem-b"], include_metadata=true, budget_chars=12000)
omega_memory(action="get", memory_id="mem-abc123", include_edges=true, max_related=5)
```

Set `track_access=false` for audits or tests. Use `content_mode="preview"` or
`content_mode="none"` when you only need metadata. For batch hydration or
edge expansion, set `budget_chars` to cap full content and inspect the returned
truncated/omitted ID lists before acting.

Use `include_edges=true` when an exact memory ID needs adjacent context such as
superseding decisions, contradicting lessons, causal predecessors, or derived
records. Related records preserve the store-level `node_id` and also expose
`id` for consistency with `omega_recall`. The related order is deterministic:
nearest hop first, strongest edge weight, edge-type priority (`supersedes`,
`contradicts`, `evolves`, `causal`, `related`, `derived_from`, then unknown
types), newest edge timestamp, then stable memory ID.

### Project Context Packs

**`omega_context(project?, mode?, query?, budget_chars?)`**

Build a compact project-scoped pack from recent checkpoints, completions,
lessons, decisions, constraints, and optional focused recall.

```text
omega_context(project="/home/akalanka/sentinel-core", mode="handoff")
omega_context(project="/home/akalanka/sentinel-core", mode="planning", query="SC-024")
omega_context(project="/home/akalanka/sentinel-core", mode="debug", format="json")
```

Use this near the start of long repo work, after `omega_welcome` and
`omega_protocol`, especially when the task may have prior checkpoints.

### Session Management

**`omega_welcome(project?)`** — Call at session start. Returns recent context, active reminders, and project state. This is how your agent picks up where it left off.

**`omega_checkpoint()`** — Save current task state mid-session. If the session ends unexpectedly, the next `omega_welcome` restores this context.

**`omega_resume_task(task_id)`** — Resume a previously checkpointed task with full context.

### Memory Maintenance

**`omega_reflect()`** — Analyze memory quality: duplicates, contradictions, coverage gaps.

**`omega_maintain(action)`** — Run maintenance operations: consolidation, compaction, health checks.

## Retrieval Architecture

OMEGA's query pipeline runs 7 phases to find the most relevant memories:

1. **Vector similarity** — Embedding search (bge-small-en-v1.5, 384-dim) via sqlite-vec
2. **Full-text search** — FTS5 with BM25 scoring
3. **Strong signal short-circuit** — Skip expensive phases when FTS5 finds an exact match
4. **Score fusion** — Reciprocal Rank Fusion combines vector + text scores
5. **Contextual boosting** — Boost results matching current file, project, or tags
6. **Cross-encoder reranking** — ms-marco-MiniLM-L-6-v2 rescores top candidates
7. **Assembly** — Dedup, normalize, apply minimum relevance threshold

This hybrid approach achieves 95.4% on LongMemEval (500-question benchmark).

## Best Practices

### What to Store

- Architectural decisions with reasoning ("chose X because Y")
- Debugging insights that took effort to discover
- User preferences stated explicitly ("always use..." / "never...")
- Cross-session context that future sessions need

### What NOT to Store

- Information already in the codebase (read the code instead)
- Transient state (build output, test results)
- Anything shorter than a meaningful sentence
- Speculative conclusions from reading a single file

### Query Patterns That Work

- **Before starting a long task:** `omega_context(project="[repo]", mode="handoff")`
- **Before making a decision:** `omega_recall("prior decisions about [feature area]", profile="planning", project="[repo]")`
- **Before modifying a file:** `omega_query(context_file="/path/to/file.py")`
- **After finding an ID:** `omega_memory(action="get", memory_id="mem-...")`
- **When browsing uncertain terms:** `omega_query(mode="browse", browse_by="recent", offset=0, format="json")`
- **After debugging:** `omega_store("[root cause and fix]", "lesson_learned")`
- **When user says "remember":** `omega_store("[what they said]", "user_preference")`

### Anti-Patterns

| Don't | Do Instead |
|-------|-----------|
| Store every tool result | Store only insights and decisions |
| Query with single words | Use natural language questions |
| Depend on 200-character previews for handoff recovery | Use `omega_recall` or `omega_memory(action="get")` |
| Guess available hidden tools in condensed mode | Call `omega_tools(category=...)` or `omega_tools(tool=...)` |
| Skip `omega_welcome` at session start | Always call it — it loads critical context |
| Store without `event_type` | Always specify type for proper TTL and dedup |
| Guess from stale memory | Query OMEGA to verify current state |

## How It Works Under the Hood

- **Storage:** SQLite with WAL mode. Single file at `~/.omega/omega.db`.
- **Embeddings:** bge-small-en-v1.5 via ONNX Runtime (~90MB RAM). LRU cache (512 entries).
- **Vector search:** sqlite-vec extension for ANN similarity search.
- **Text search:** FTS5 with BM25 ranking.
- **Dedup:** Jaccard similarity with per-type thresholds (0.70-0.90). Content-level and embedding-level.
- **Memory evolution:** Similar memories merge (Zettelkasten-style) instead of creating duplicates.
- **TTL:** Automatic expiry based on event type. Permanent for preferences, 7-90 days for others.
- **Privacy:** Everything stays local. No cloud, no telemetry. Apache-2.0 licensed.

## Links

- **PyPI:** [omega-memory](https://pypi.org/project/omega-memory/)
- **GitHub:** [omega-memory/omega-memory](https://github.com/omega-memory/omega-memory)
- **Docs:** [omegamax.co/docs](https://omegamax.co/docs)
- **Benchmarks:** [omegamax.co/benchmarks](https://omegamax.co/benchmarks)

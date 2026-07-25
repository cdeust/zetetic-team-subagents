#!/usr/bin/env python3
"""
Patch 6: Add <memory-architecture> section to all 117 agents.

Clarifies the three-tier memory model (from Letta/MemGPT context engineering):
  Tier 1 — System (pinned, cache-busting if modified mid-session)
  Tier 2 — Working memory (on-demand, cache-neutral tool calls)
  Tier 3 — Cortex semantic index (async/eventual, not system memory)

Injected BEFORE the existing <memory> section in each agent file.
"""
import os

AGENTS_DIR = os.path.join(os.path.dirname(__file__), "..", "agents")

MEMORY_ARCH_SECTION = """\
<memory-architecture>
## Three-Tier Memory Architecture

Agents operate across three distinct memory tiers. Confusing them wastes tokens, busts caches, or loses state. Know which tier to read from and write to at every step.

```
Tier 1 — SYSTEM (pinned, cache-sensitive)
  ├── This agent's .md file (the system prompt itself)
  └── Cortex session-start recall (loaded once at spawn)

Tier 2 — WORKING MEMORY (on-demand, cache-neutral)
  └── /memories/<scope>/          ← your subtree
        ├── checkpoint.md         ← task progress (overwrite as you go)
        ├── notes.md              ← rejected approaches, confirmed constraints
        └── scope-history.md      ← scope deltas received mid-task

Tier 3 — CORTEX SEMANTIC INDEX (async, eventually consistent)
  ├── cortex:remember             ← write to semantic index
  └── cortex:recall               ← semantic search across sessions
```

### Tier 1 — System (pinned)
**What it is:** The agent's `.md` definition file is the system prompt. It is loaded once at session start and KV-cached. All tool definitions, earlier turns, and the cached system prompt share the same cache key.

**Cache rule:** Modifying the system prompt mid-session **busts the entire KV cache** — every cached token must be reprocessed. This is expensive (full context reload at cost).

**When to update:** Only at compaction events — session end, checkpoint write, or significant role/identity change that must persist across all future sessions. **Never mid-task.**

**Opus 4.8 exception:** Mid-conversation system messages (the `"system"` role in conversation history) are cache-safe incremental updates — they do not modify the top-level system prompt, so the cache stays intact. Use these for token-budget updates, permission changes, and scope narrowing mid-task.

### Tier 2 — Working Memory (on-demand, cache-neutral)
**What it is:** Files in your `/memories/<scope>/` subtree. Read via `tools/memory-tool.sh view` (a tool call). Written via `tools/memory-tool.sh create/str_replace`.

**Cache rule:** Tool calls are cache-neutral — they do not modify the system prompt or conversation history structure. Reading a memory file costs only the tokens in the response, not a full cache bust.

**Progressive disclosure:** Only read the files you need, when you need them. Do NOT load all memory files at session start — that wastes context on stale data. Load `checkpoint.md` on restart; load `notes.md` only when hitting a known decision point; load `scope-history.md` only when the task scope seems to have drifted.

**When to write:** As you make decisions, complete subtasks, or discover constraints. Overwrite `checkpoint.md` incrementally. Keep files focused and under 50K each.

### Tier 3 — Cortex Semantic Index (async, eventual)
**What it is:** The Cortex MCP server (`cortex:remember`, `cortex:recall`, `cortex:unified_search`). A semantic similarity index over all sessions, all agents, all projects.

**What it is NOT:** It is not system memory. It is not working memory. It is a semantic retrieval surface — useful for cross-session "what do I know about X?" queries, not for deterministic state recovery.

**Cache rule:** `cortex:recall` is a tool call — cache-neutral. Writing via `cortex:remember` queues an async sync; local `/memories/` files are updated synchronously.

**When to use:**
- `cortex:recall` — conceptual retrieval when you don't know which file contains the answer
- `cortex:remember` — after completing significant work worth surfacing to ALL future sessions across ALL agents
- Do NOT use `cortex:remember` for task-specific checkpoint data — that belongs in Tier 2

### Decision guide: which tier to write to?

| Write when... | Write to | Tier |
|---|---|---|
| Completing a task session — progress, decisions, next action | `/memories/<scope>/checkpoint.md` | 2 |
| Discovering a constraint that affects future sessions too | `cortex:remember` + `/memories/<scope>/notes.md` | 2 + 3 |
| A scope change was received mid-task | `/memories/<scope>/scope-history.md` | 2 |
| A cross-agent lesson was learned | Propose to orchestrator (you can't write `/memories/lessons/`) | — |
| The agent's role or rules need permanent change | Edit the `.md` file at session end (compaction) | 1 |
| Mid-task token budget or permission update | Mid-conversation system message (harness injects, cache-safe) | 1* |

### Cache-safe update path (Letta pattern, Opus 4.8)
Rather than recompiling the full system prompt on every memory update:
1. **Task execution** → write decisions to Tier 2 (cache-neutral)
2. **Checkpoint event** → signal `CHECKPOINT`, save to Tier 2, let harness recompile if needed
3. **Session end** → Cortex async sync drains the write queue (Tier 3 updated from Tier 2)
4. **Next session start** → Tier 1 (system prompt) loads fresh; Cortex recall retrieves relevant Tier 3 context; Tier 2 checkpoint loaded on first tool call

This is progressive disclosure: only `/system` (Tier 1) is always in context. Everything else is retrieved when needed.
</memory-architecture>
"""


def patch_file(path: str) -> bool:
    with open(path) as f:
        content = f.read()

    if "<memory-architecture>" in content:
        return False

    # Insert before <memory> section if it exists, otherwise append
    if "\n<memory>" in content:
        content = content.replace("\n<memory>", "\n" + MEMORY_ARCH_SECTION.rstrip() + "\n\n<memory>", 1)
    else:
        content = content.rstrip() + "\n\n" + MEMORY_ARCH_SECTION.rstrip() + "\n"

    with open(path, "w") as f:
        f.write(content)
    return True


def main():
    changed = skipped = 0

    for fname in sorted(os.listdir(AGENTS_DIR)):
        if not fname.endswith(".md"):
            continue
        path = os.path.join(AGENTS_DIR, fname)
        if patch_file(path):
            changed += 1
            print(f"  patched: agents/{fname}")
        else:
            skipped += 1

    genius_dir = os.path.join(AGENTS_DIR, "genius")
    for fname in sorted(os.listdir(genius_dir)):
        if not fname.endswith(".md"):
            continue
        path = os.path.join(genius_dir, fname)
        if patch_file(path):
            changed += 1
            print(f"  patched: agents/genius/{fname}")
        else:
            skipped += 1

    print(f"\nDone: {changed} patched, {skipped} skipped")


if __name__ == "__main__":
    main()

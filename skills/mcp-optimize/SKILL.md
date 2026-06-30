---
name: mcp-optimize
description: Audit local MCP server config and tool-loading context cost; report deferred vs loaded-upfront servers with estimated token cost and copy-pasteable optimization levers, plus an optional gated --apply.
---

Audit MCP tool-loading context cost in this Claude Code session and recommend concrete configuration levers to reduce it, while keeping operator-pinned servers eagerly loaded. REPORT-only by default — an optional `--apply` writes only local settings files, gated by per-change confirmation, backup, and JSON validation.

**IMPORTANT:** This skill runs directly — do NOT invoke the `orchestrator` agent or any other agent. Execute every stage yourself using the tools available to you (Bash, Read, Grep, Glob, and Write/Edit only inside the gated `--apply` path).

## Voice

You speak as a professional instrument: formal, neutral, declarative. The following rules apply to every response you produce — chat replies, status blocks, workspace doc prose, memory writes, self-corrections, apologies, and error messages. There is no informal-chat-mode loophole.

**Forbidden in any response:**
- Enthusiasm markers: "Perfecto", "Excelente", "Genial", "Listo", "Great", "Excellent".
- Emoji decoration of routine status (`✅`, `⚠️`, `🎉`, `✨`).
- First-person personality: "Creo que", "Me parece", "I think", "I believe".
- Anthropomorphic framing: "Yo voy a", "I'll go", "Quiero ayudarte", "Let me".
- Affirmations directed at the operator: "Buena pregunta", "Tenés razón", "That makes sense".
- Filler closings: "Espero que esto te sirva", "Hope this helps", "Let me know if anything else comes up".
- Colloquialisms: regional slang, "shippeo", "bakeado", "wrappear".
- Marketing tone: "potente", "innovador", superlatives.

**Required:**
- Declarative statements of fact: "Three servers load upfront", "Two settings files were read".
- Direct action descriptions: "X was read", "Y is recommended", "Z requires operator confirmation".
- Concise summaries: a status block, a table, or a 2-3 sentence outcome. No padding, no celebration.

The operator can chat in any language; you reply in the operator's chat language, but the voice rules above apply regardless of language.

---

## Arguments

| Argument | Description |
|----------|-------------|
| (none) | Run Stages 1-4 (inventory, enumerate, classify, recommend) and present the REPORT-only output. No file on disk is modified. |
| `--apply` | After the report, offer each recommended config edit individually for confirmation and apply confirmed changes to local settings files only. See `## --apply Mode`. |
| `--pin <name1,name2,...>` | Extend the operator-pinned allowlist beyond the default (`memory`). Pinned servers are never recommended for deny/disable and are recommended for `alwaysLoad: true` instead. |
| pasted `/context` snapshot | If the operator pastes a `/context` command output as part of (or immediately after) the invocation, Stage 3 uses those real per-category figures instead of the modeled estimate. |
| `--help` | Print the stage list and the REPORT/`--apply` contract; do not run the audit. |

---

## Execution

### `--help` path

If `$ARGUMENTS` contains `--help`, print the following and exit without running the audit:

```
/th:mcp-optimize — MCP tool-loading context audit and optimization

Stages:
  1 (inventory)   — read every local config file, list configured servers + levers
  2 (enumerate)   — run `claude mcp list` to enumerate the loaded server set
  3 (classify)    — tag deferred vs loaded-upfront, render a /context-style cost estimate
  4 (recommend)   — emit copy-pasteable config edits; never touch a pinned server

Default: REPORT-only. No file on disk is modified.
--apply: gated mutation of local settings files only — backup + per-change confirm +
         JSON-parse validation before and after. Never touches claude.ai cloud settings.
         Never disables a pinned server (default pin: memory; extend with --pin).

Pasted /context snapshot: when present, Stage 3 uses real figures instead of the estimate.
```

### Stage 1 — Inventory (config read)

1. Read, if present, each of these files (use Read; treat a missing file as "absent", not an error):
   - `~/.claude.json` — top-level `mcpServers` key (user-scoped server definitions)
   - `~/.claude/settings.json` — user-scoped settings
   - `.claude/settings.json` — project-scoped settings
   - `.claude/settings.local.json` — project-scoped local overrides
   - `.mcp.json` — project-scoped server definitions
   - the system managed-policy file, best-effort (path varies by OS — e.g. `/etc/claude-code/managed-mcp.json` on Linux, `/Library/Application Support/ClaudeCode/managed-mcp.json` on macOS, `%PROGRAMDATA%\ClaudeCode\managed-mcp.json` on Windows). Typically unreadable without admin rights — skip silently if absent or unreadable, do not report this as a finding.
2. For each configured server found in `mcpServers` (any source file), extract:
   - name, transport (`stdio` when a `command` key is present; `http`/`remote` when a `url` key or `"type": "http"` is present), `alwaysLoad` flag, and the source file it was read from.
3. Across every settings file read, extract the current state of: `disableClaudeAiConnectors`, `deniedMcpServers`, `allowedMcpServers`, `allowManagedMcpServersOnly`, `allowAllClaudeAiMcps`, `env.ENABLE_TOOL_SEARCH`, `env.ENABLE_CLAUDEAI_MCP_SERVERS`. Report "not set" when a key is absent from every source (tool search defaults to on; the connector/deny keys default to unset).
4. **Never echo secret material.** Read for structure only — server names, transport, flags, key presence/absence. Never reproduce `env` values, `headers` values, tokens, or URLs that embed credentials in the report. If a server's `env` block is non-empty, name the variable keys only (never their values).

### Stage 2 — Enumerate (loaded set)

1. Check `command -v claude`. If absent, skip to step 4.
2. Run `claude mcp list` via Bash. This lists every server the CLI can see — both locally-configured servers and claude.ai account connectors — with a connection-status indicator. It does not print per-server tool counts; do not attribute a tool count to a server from this command's output.
3. Parse each output line into `{display-name, endpoint-or-command, transport-hint, status}`. Lines prefixed `claude.ai ` are cloud connectors; all other lines are locally-configured servers (cross-reference by name against Stage 1's inventory).
4. Cross-reference the enumerated set against the Stage 1 inventory:
   - A claude.ai connector present in the enumeration but absent from `~/.claude.json` → flag as "loaded but not present in local config (claude.ai account connector)".
   - A locally-configured server absent from the enumeration → flag as "configured but not connected" (do not speculate on cause beyond reporting the CLI's status text).
5. **Degrade gracefully.** If `claude` is absent, or `claude mcp list` errors or returns no output, report the enumeration as "unavailable — claude CLI not found or did not respond" and continue with Stages 3-4 using the Stage 1 config-only inventory. Do not fail the skill.

### Stage 3 — Classify + breakdown

1. Classify every server known from Stage 1 and/or Stage 2:
   - `stdio` transport → **deferred** (tool search applies; cheap until invoked).
   - `http`/`remote` transport (non-claude.ai) → **loaded upfront (not reliably deferred)** — cite: HTTP/Streamable-HTTP MCP tools are not reliably deferred by tool search regardless of the `ENABLE_TOOL_SEARCH` setting (anthropics/claude-code#40314, closed as not planned).
   - claude.ai connector → **loaded upfront (not reliably deferred)** — same citation; cloud connectors are HTTP transport.
   - any server whose name matches the pinned allowlist (default `memory`, extended by `--pin`) → annotate **pinned — kept eager**, regardless of its transport classification above.
2. Render a `/context`-style breakdown. Two paths:
   - **No pasted snapshot (default):** build a labeled ESTIMATE. State the heuristic explicitly: approximately 580 tokens per loaded tool (anchor observation: 139.1k tokens / 240 tools in a representative session), and an assumed 8-20 tools per HTTP/remote or claude.ai connector when the exact count is unknown (state this assumption inline, do not present it as measured). Present a table:

     | Category | Tokens (estimate) | % of 200k window (estimate) |
     |---|---|---|
     | MCP — stdio (deferred) | ~{N} | ~{N}% |
     | MCP — HTTP/remote (loaded upfront) | ~{N} | ~{N}% |
     | MCP — claude.ai connectors (loaded upfront) | ~{N} | ~{N}% |
     | MCP — pinned, eager by design | ~{N} | ~{N}% |
     | System prompt / tools / memory / skills | not locally auditable — paste a `/context` snapshot for real figures | — |

     Mark every figure in this path with "(estimate)" inline — never present it as measured.
   - **Pasted `/context` snapshot present:** parse the operator-supplied snapshot for its real per-category token figures and substitute them into the same table shape, replacing "(estimate)" with "(from pasted snapshot)".

### Stage 4 — Recommend

1. Before emitting any recommendation in this stage, check whether any pinned server (default `memory`, plus any `--pin` names) is itself a claude.ai connector (per the Stage 2 cross-reference). Record this as `pin_includes_cloud_connector` (true/false) — it gates step 2 below.
2. For every server classified "loaded upfront (not reliably deferred)" that is **not** pinned, emit the exact copy-pasteable edit:
   - To disable every claude.ai connector at once: `{"disableClaudeAiConnectors": true}` added to `~/.claude/settings.json` — **only when `pin_includes_cloud_connector` is false**. When `pin_includes_cloud_connector` is true, do NOT recommend this global lever (it would disable the pinned connector too, defeating the pin) — recommend only the targeted `deniedMcpServers` entries below for the specific unpinned connectors, and state explicitly that the global lever was skipped because a pinned server is a claude.ai connector.
   - To deny one specific connector or server without disabling all: `{"deniedMcpServers": [{"serverName": "<display-name>"}]}` (or `{"serverUrl": "<url-pattern>"}` when the URL is known — more rename-robust than `serverName`). When emitting `serverUrl`, derive it as host+path only: strip userinfo (anything before `@` in the authority) and the query string before emitting. If stripping would leave the URL uninformative (e.g. empty path), fall back to `serverName` instead — never reproduce a raw URL that embedded credentials (per the Stage 1 no-secret rule, line 80).
3. For every pinned server (default `memory`, plus any `--pin` names): recommend `"alwaysLoad": true` on that server's entry in `~/.claude.json` / `.mcp.json`. **Never** emit a `deniedMcpServers` or `disableClaudeAiConnectors` recommendation that would affect a pinned server — see step 1's `pin_includes_cloud_connector` gate.
4. Report the current `ENABLE_TOOL_SEARCH` state:
   - Unset or `true` → "on by default; defers stdio servers but does not reliably defer HTTP/remote or claude.ai connectors (#40314) — does not address the dominant cost driver in most sessions."
   - Explicitly `false` → recommend removing the override (re-enabling default deferral) for stdio servers.
   - `auto`/`auto:N` → report the configured threshold; no change recommended.
5. Summarize estimated savings if every non-pinned "loaded upfront" recommendation were applied: estimated tokens reclaimed, resulting percentage of the context window, and a rough qualitative per-session cost delta (e.g. "fewer tokens consumed at the start of every session"). Label every figure "estimate" unless derived from a pasted snapshot.
6. Note any claude.ai connector toggle that lives in the cloud account UI (out of local reach) as a manual operator action, distinct from the local settings-file levers above.

---

## --apply Mode

Triggered only when `$ARGUMENTS` contains `--apply`. Runs after the Stage 1-4 report is presented.

1. Build the list of apply-able changes from Stage 4 — config-file edits only. Never include a cloud/claude.ai account setting, never include an edit to the managed-policy file, and never include a deny/disable edit for a pinned server.
2. For each change, present it individually in chat (file, exact key/value, one-line reason) and wait for an explicit operator reply before acting. A change with no explicit "yes" is skipped, not assumed.
3. For each confirmed change:
   a. Back up the target file first, to a fixed location OUTSIDE any git working tree: `~/.claude/.mcp-optimize-backups/<basename>.bak-<UTC timestamp>` (create the directory if absent). Never write the backup adjacent to a project-scoped target (`.claude/settings.json`, `.claude/settings.local.json`, `.mcp.json`) — those live inside the project's git working tree and an accidental `git add` would commit secret material. After copying, set the backup file's mode to `0600` explicitly (e.g. `chmod 600 <backup-path>`) — do not rely on umask, since the source file (especially `~/.claude.json`, which may hold `env`/token values) can carry secrets. Backups are not auto-retained or auto-deleted; report the backup path to the operator so they can remove it once no longer needed.
   b. Validate the current file parses as JSON before editing — pass the path as a positional argument, never interpolated into the `-c` source string: `python3 -c 'import json, sys; json.load(open(sys.argv[1]))' "<path>"`, falling back to `node -e 'require(process.argv[1])' "<path>"` if `python3` is unavailable. Abort this change and report the parse error if validation fails — do not write to a file that does not already parse.
   c. Merge-write only the specific key for this change, preserving every other key and value untouched. Never replace the file wholesale.
   d. Validate the file parses as JSON again after the write (same positional-argument form as step b). If it does not, restore from the backup taken in step (a) and report the failure.
   e. Report the file changed, the key/value applied, and the backup path.
4. If the operator declines every offered change, report "no changes applied" and stop. No file is touched.
5. `--apply` never writes outside `~/.claude/settings.json` and `~/.claude.json` (or their project-scoped equivalents `.claude/settings.json` / `.claude/settings.local.json` / `.mcp.json` when the recommended edit targets a project-scoped server). It never touches the managed-policy file and never touches claude.ai account/cloud settings — those remain manual operator actions per Stage 4 step 6.

If `--apply` is NOT present, skip this section entirely — the run is REPORT-only and no file on disk is modified.

---

## Output Format

Present the consolidated report using this shape:

```
====================================
  /th:mcp-optimize — MCP Tool-Loading Audit
====================================

--- Stage 1: Inventory ---
Configured servers: {N} across {M} source files
  {name} — {transport} — {source file} — alwaysLoad: {true|false}
  ...
Levers: disableClaudeAiConnectors={state} | deniedMcpServers={N entries|none} |
        allowedMcpServers={N entries|none} | ENABLE_TOOL_SEARCH={state}

--- Stage 2: Enumerate ---
{claude CLI available: N servers enumerated, M claude.ai connectors |
 claude CLI unavailable — enumeration skipped, config-only audit}
Loaded but not locally configured: {list or "none"}
Configured but not connected: {list or "none"}

--- Stage 3: Classify + breakdown ---
  {name} — {deferred | loaded upfront (not reliably deferred, #40314) | pinned — kept eager}
  ...
{breakdown table per Stage 3, labeled estimate or from pasted snapshot}

--- Stage 4: Recommendations ---
  {N} recommended edit(s):
  {exact copy-pasteable JSON/key for each}
Pinned (kept eager, never denied): {list}
Estimated savings if applied: ~{N} tokens (~{N}% of window) — estimate
Manual cloud-account actions: {list or "none"}

====================================
  Mode: {REPORT-only | --apply (N confirmed / M offered)}
====================================
```

---

## Output Discipline

See `agents/_shared/output-template.md` § "Output Discipline" for the full contract. Each Bash/Read/Grep/Glob call runs silently — only the consolidated Stage 1-4 report (and, when `--apply` is present, the per-change confirmation prompts and their outcomes) are presented to the operator. No intermediate tool-call narration.

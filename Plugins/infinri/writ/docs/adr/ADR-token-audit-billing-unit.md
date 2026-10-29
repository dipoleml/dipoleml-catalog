# ADR: token-audit bills per API response, prices per model, and adds up the subagent tree

Status: accepted
Date: 2026-09-29
Plan: `.claude/plans/54fe1ac9-a554-401f-bbe7-2419043b40f2/plan.md`
Touches: `writ/analysis/token_audit.py`, `writ/analysis/token_tree.py`, `writ/cli.py`,
`writ/analysis/efficacy_ab.py`, `tests/test_token_audit.py`,
`tests/test_token_audit_accounting.py`, `tests/test_token_audit_tree.py`,
`tests/test_efficacy_ab.py`, `tests/fixtures/token_audit_helpers.py`; Task 2:
`hooks/scripts/writ-subagent-stop.sh`, `writ/shared/logging.py`,
`tests/test_subagent_usage_summary.py`

## Context

`writ token-audit` is the denominator instrument: every later model, effort or routing
experiment reads its dollar figure. Four defects made that figure wrong.

1. **Record-level double billing.** `parse_turns` appended every `type == "assistant"`
   record that carried `message.usage`. Claude Code writes one record per content block of
   a single API response, and every one of those records repeats the same `message.id` and
   the same `message.usage`. On the session that motivated this change there were 116
   assistant records but 64 unique `message.id`; output counted 105,770 against 49,675
   deduped, and cache_read 17,040,667 against 9,401,992. Every measured figure, the
   compounding curve, the compaction segments and the attributed re-read cap inherited the
   inflation.
2. **One model for the whole transcript.** Every turn was priced with the CLI `--model`
   (default `claude-opus-4-8`) times universal COST_WEIGHTS. The per-record model was
   parsed and never read, so mixed-model sessions, dated ids such as
   `claude-haiku-4-5-20251001`, and models whose cache-read ratio is not 0.1x
   (`claude-opus-5-5` at 0.05x, `claude-fable-5-1` at 0.025x) priced wrongly or not at all.
3. **Subagents ignored.** Main-thread usage lives in the main transcript; each subagent's
   usage lives only in `<session>/subagents/agent-<id>.jsonl`. The audit read only the main
   file, so all subagent spend was missing.
4. **Subagent transcripts are ephemeral.** Claude Code deletes them; after that the spend
   is unrecoverable unless something records it at SubagentStop (Task 2, appended later).

## Decision

### Billing unit: the API response, keyed by `message.id`

One response per unique `message.id`. `requestId` is not used as a key; the validation
below checks whether it maps 1:1 with `message.id`.

- Records with no `message.id` are each a separate response. Every pre-existing fixture is
  id-less, so their totals are unchanged.
- Every repeat of an id is counted in `duplicates_collapsed` (records minus responses).
  The LAST record in file order supplies usage and model, because it is the latest snapshot
  of the response. The response keeps the position of its FIRST record, so turn order for
  the compounding curve and segments is stable. The records of one id are then classified
  three ways:
  1. **Identical:** every record has the same `usage` and `model`. Collapsed silently.
  2. **Streaming snapshot:** the model is the same on every record, every non-output usage
     field is identical (`input_tokens`, `cache_read_input_tokens`,
     `cache_creation_input_tokens`, and the `cache_creation` 5m/1h split), and
     `output_tokens` never decreases across the records in file order and increases at
     least once. This is Claude Code writing a response's usage while it is still
     streaming. No warning is emitted; the response is counted once in
     `streaming_snapshot_updates`.
  3. **Conflict:** anything else, meaning the model differs, any non-output field differs,
     or output decreases at any step. A `duplicate_id_conflict` warning names the id, the
     record count and the differing fields (`usage`, `model`), and the response is counted
     in `duplicate_conflicts`.
- `measured` (main thread) and `aggregate_file_usage` (per file) both expose
  `streaming_snapshot_updates` and `duplicate_conflicts`. The per-file `conflicts` key stays
  equal to `duplicate_conflicts`, so the Task 2 summary row contract holds. The ACCOUNTING
  WARNINGS section of `render_text` prints the session-wide totals over the main thread
  plus accounted dispatches, for example `records 117, responses 62, collapsed 55,
  streaming_snapshot_updates 26, duplicate_conflicts 0`.
- Rejected: warning on every repeat whose usage differs. Streaming snapshots are the normal
  case on real transcripts, so the real conflicts would be buried under noise.
- A `message.id` seen in two files of one tree is counted once (main first, then walk
  order) and warns `cross_file_duplicate_id`. The evidence says this does not happen; it is
  an invariant check. The dropped response's records also leave the later file's `records`
  count, so that file's `duplicates_collapsed` (records minus responses) counts only its own
  in-file repeats and is not inflated by the cross-file drop. `aggregate_file_usage` on one
  file alone has no cross-file context and keeps the full count.
- `parse_turns` keeps its signature and return shape but returns deduped responses. The
  schema canary still runs on the main transcript before anything is computed, and a
  subagent or orphan file whose usage record lacks a required field raises the same
  `TokenAuditSchemaError` (CLI exit 2).

Rejected: billing per record. It is what the code did, and it double-bills every
multi-block response.

### Rate card: USD per MTok per model, five categories

`RATE_CARD` holds `input`, `output`, `cache_read`, `cache_write_5m` and `cache_write_1h`
for exactly the approved models; `"<synthetic>"` (Claude Code internal, never billed) is
all zeros and never reported as unpriced. The 5m/1h split comes from the existing
`_split_cache_creation`; an unsplit `cache_creation_input_tokens` prices as 5m, the cheaper
tier, so the figure never overstates. `INPUT_USD_PER_MTOK` is derived from the card, so its
existing keys keep their values for importers.

For opus-4-8/4-7/4-6, sonnet-4-6, haiku-4-5 and fable-5 the card equals COST_WEIGHTS times
the old input rate exactly, so on the same deduped responses the new USD equals the old
formula; a test pins this. `COST_WEIGHTS`, `weighted_cost`, `compounding_curve`,
`segment_lengths`, `attribute_writ`, `attribute_prevented` and `render_json` are unchanged
(corpus_footprint and injection_footprint import them).

Rejected: universal multipliers on a per-model input rate. They are wrong for every model
whose cache-read ratio is not 0.1x.

### Model normalization and precedence

`normalize_model(raw)` returns the exact RATE_CARD key, or the base of a trailing
`-YYYYMMDD` suffix when that base is an exact key, else None. There is no prefix or fuzzy
matching: `claude-opus-5-6` is unpriced and never priced as 5.5.

Per response, the record's `message.model` is authoritative when it is a non-empty string,
even if it does not normalize. Only a record with no model uses the `scorecard` `model`
argument (CLI `--model`) as a fallback. Anything else is UNPRICED. The CLI default changed
from `claude-opus-4-8` to None, because a default fallback silently prices model-less
records as Opus, which is a guess. `scorecard(transcript_path, friction_path, model)` keeps
its positional signature; efficacy_ab still passes `claude-opus-4-8`, which is now only a
fallback.

### Unpriced and partial semantics

- `card["unpriced"]` lists every unpriced model key (raw id, or `"<none>"` for model-less
  records) across the main thread and all accounted dispatches, with raw token counts and
  a `scope` list (`"main"` and dispatch ids). Each adds an `unpriced_model` warning.
- `measured` stays MAIN THREAD ONLY and keeps every legacy key. `measured.total_cost` is the
  unchanged COST_WEIGHTS weighted-token score over deduped responses (also exposed as
  `weighted_token_cost`). `measured.total_usd` is the priced main-thread USD when at least
  one main-thread response is priced, a floor when `usd_partial` is true, and None when no
  main-thread response is priced.
- `session.partial` is true iff the main thread or any accounted dispatch has unpriced
  usage, or any dispatch is `missing_transcript` or `missing_metadata`.
- `render_text` never presents a partial figure as the total: the TOTAL and session lines
  say PARTIAL and name the unpriced response count.

### Tree linkage (`writ/analysis/token_tree.py`)

Linkage is kept out of the pricing module. The session directory is the transcript path
without `.jsonl`. Subagent files are indexed from `subagents/agent-*.jsonl` (layout
`flat`) and `subagents/*/*/agent-*.jsonl` (layout `workflow`), with the sibling
`.meta.json` sidecar (`agentType`, `toolUseId`, `spawnDepth`, `model`, `stoppedByUser`);
agent ids pass the same allowlist shape as `subagent_role._VALID_AGENT_ID`.

A dispatch is an assistant `tool_use` block named `Agent`. It links to an agent id through
the matching user record's top-level `toolUseResult.agentId`, else through the file whose
`meta.toolUseId` equals the dispatch id. The walk starts at the main transcript and
recurses into each accounted subagent's own transcript (parent dispatch id, depth + 1, a
visited set against cycles); a nested child is found wherever its file sits in the index.
A second dispatch resolving to an already-linked agent is dropped with a
`duplicate_agent_link` warning so no file is billed twice. Those drops are counted in
`dispatch_coverage.duplicate_links`. They are not in `dispatches` or `accounted`, add
nothing to any session total, and do not set `session.partial`: the spend they point at is
already billed once through the first link.

Each dispatch is `accounted` (source `transcript`), `missing_transcript` (agent id known,
no file) or `missing_metadata` (no agent id resolvable). Every indexed file the walk never
reaches is an orphan: priced and listed in `orphans` with layout, spawn depth and role, but
EXCLUDED from the session total, with the excluded dollars shown as
`session.orphan_usd_excluded`. Workflow-layout files have no Agent tool_use in the main
thread, so they always surface as orphans and `dispatch_coverage.workflow_layout` reads
`"unsupported: listed as orphans, not in session total"`.

Role is `meta.agentType`, else the dispatch input `subagent_type`, else `"unknown"`, with a
leading `"writ:"` stripped; the main thread's role is `"main"`.

Rejected: summing every file under `subagents/`. It counts files that belong to no
dispatch of this session (workflow runs, stale files), and it cannot say which dispatches
are missing.

### Attribution outputs and invariant

New card keys: `session`, `cost_by_model`, `cost_by_role`, `cost_by_dispatch`, `orphans`,
`dispatch_coverage` and `reconciliation`. The existing friction-advisory `coverage` key is
untouched, which is why the new one is named `dispatch_coverage`.

Invariant, asserted in tests: `session.total_usd == main_usd + sum(usd of every accounted
dispatch at every depth) == sum(cost_by_model usd) == sum(cost_by_role usd)`. All sums use
the priced floor; orphans are never in them.

### Cost-state reconciliation

The LAST `type == "cost-state"` record of the main transcript is compared with the Writ
session figure. The record is flat, verified against a real Claude Code transcript: the
top level carries `type`, `sessionId`, `totalCostUSD`, `modelUsage`,
`hasUnknownModelCost`, `startTime` and the duration and lines-changed totals, and each
`modelUsage[model]` entry carries `inputTokens`, `outputTokens`, `cacheReadInputTokens`,
`cacheCreationInputTokens`, `costUSD`, `thinkingTokens` and `webSearchRequests`. Model keys
can be dated (`claude-haiku-4-5-20251001`) and are normalized with `normalize_model`
before comparison. Only this flat shape is read. The report carries
`cc_total_usd`, `writ_session_usd`, `delta_usd` (writ minus cc),
`has_unknown_model_cost`, and per-model USD and token differences. `scope` is derived from
the data: `main_only` when cost-state per-model tokens equal the main-thread totals,
`main_plus_subagents` when they equal main plus the accounted tree, else
`superset_or_unknown` (expected when cost-state lists models the tree never used, such as
Claude Code internal calls). `writ_partial` copies `session.partial`: when it is true the
Writ side of `delta_usd` is a priced floor, so a negative delta may be a coverage gap rather
than a pricing error, and the `render_text` RECONCILIATION line ends with
`(Writ figure is a floor)`. It never raises and never changes the exit code; absent, it is
`{present: false}`.

### Experiment harness (removed)

The efficacy_ab harness was removed on 2026-09-29 because it spawned headless `claude -p`
sessions, and Writ workflows never run headless Claude Code. Model and effort choices are
made from guidance and judged from real-session cost: Claude Code's own session cost, with
`writ token-audit` for attribution. Read `session.total_usd`, and treat a session as an
incomplete observation when `session.partial` is true or `session.orphan_usd_excluded > 0`;
an incomplete observation must never be read as a cheaper completed task. The references to
efficacy_ab elsewhere in this ADR are the record of the change as it was made.

## Consequences

- Dollar figures drop on every multi-block session (dedup) and rise on every session with
  subagents (tree). Neither is comparable with pre-change numbers.
- An unknown model is visible (unpriced list, warning, PARTIAL label) instead of silently
  priced as Opus or dropped.
- Workflow-layout subagent spend is listed but not attributed to the session; that limit
  is stated in the output rather than hidden.
- Spend in a subagent whose transcript Claude Code has already deleted appears only as a
  `missing_transcript` gap with `session.partial` true, unless a durable `subagent_usage`
  summary (Task 2, below) exists for it.

## Validation result: requestId to message.id mapping

Command, run against the session transcript `T` named in the plan's validation step:

    jq -s '[.[] | select(.type=="assistant" and .message.id != null) | [.message.id, .requestId]] | unique | {pairs: length, ids: (map(.[0])|unique|length), reqs: (map(.[1])|unique|length)}' "$T"

If `pairs == ids == reqs`, `requestId` and `message.id` are 1:1 on that transcript.

Observed on a snapshot of session `54fe1ac9-a554-401f-bbe7-2419043b40f2` (2026-09-29): `pairs 56, ids 56, reqs 56`, so the two keys are 1:1 and `message.id` stays the dedup key. On the same snapshot the audit's 56 responses, 57,700 output tokens and 10,704,650 cache-read tokens equal an independent Python dedup count exactly.

Conflicting duplicates in real data: across the full session tree (main plus 9 subagents), 26 response ids carried differing usage. In all 26, only `output_tokens` differed and the last record held the largest value (streaming snapshots written before the final count). Last-record-wins is therefore the correct rule; a first-record rule would undercount output.

## Decision (Task 2): durable subagent usage summaries

### Location: a `subagent_usage` event on the existing `metrics` stream

At SubagentStop, `writ-subagent-stop.sh` appends one `subagent_usage` row per subagent to
`<log_root>/<project>/metrics.jsonl` through `bin/lib/friction-append.py --stdin-json`, the
same writer `subagent_complete` uses. STREAM_MAP classifies the event as `metrics`, beside
`subagent_complete`.

- It reuses the one sanctioned writer: the durable `_fallback.jsonl` on a write failure,
  the per-project scoping, and the state root that survives plugin upgrades
  (ADR-state-root).
- `read_streams(project, ["metrics"])` already unions the live file with its rotated
  `archive/*.jsonl.gz` generations, so rotation does not hide a summary within the 90-day
  metrics retention. A summary older than that retention is lost; this is accepted.
- The lifecycle census reads one stream for both `subagent_complete` and `subagent_usage`.

Rejected: a separate per-agent file store. It would be a second persistence path with its
own retention, sanitization and fallback behavior.

### Row shape: tokens only

`{event: "subagent_usage", session: <agent_id>, agent_id, parent_session, dispatch_id,
role, role_source, status: "ok"|"no_transcript"|"error", schema: 1, responses, records,
duplicates_collapsed, streaming_snapshot_updates, conflicts, model_usage{<raw model>:
{responses, input, output, cache_read, cache_write_5m, cache_write_1h}},
child_dispatches{<tool_use_id>: <agent_id or null>}, first_ts, last_ts}`.

- Dollars are never stored. A rate-card correction therefore applies retroactively when a
  summary is priced at audit time.
- Model ids are stored raw (`claude-haiku-4-5-20251001`); normalization and the `--model`
  fallback for the `"<none>"` key happen at audit time.
- `dispatch_id` is the `toolUseId` of the transcript's sibling `.meta.json`, else of the
  sidecar `subagent_role.sidecar_path` finds for the agent id, else null. The lookup is
  guarded: any exception from the meta read or the sidecar search yields a null
  `dispatch_id`, never an exception and never a status change, so an aggregation that
  succeeded still writes an `ok` row. `role` is normalized (leading `writ:` stripped) and
  `role_source` records where it came from.
- `child_dispatches` lets the audit continue into nested children after the parent
  subagent's transcript is gone.
- The row is built by `usage_summary_event`, which wraps `aggregate_file_usage`, so the hook
  and the audit apply the same dedup rule (including the streaming-snapshot rule) by
  construction.
- `no_transcript`: no path resolved, or the file does not exist. The parent-collapse
  refusal of `resolve_subagent_transcript` lands here, so a collapsed payload never records
  the parent's usage as the subagent's. `error`: reading the file or the schema check
  failed (the exception class name is recorded). Neither status carries usage.

### The hook never blocks the stop

The block runs after role resolution and before the `subagent_complete` block, as a
single-quoted `python3 -c` piped to friction-append with stderr and stdout discarded and
`|| true`. It prints nothing to the hook's stdout, because a Stop-family
additionalContext acts as a turn block. Any failure becomes an `error` row or no row; the
hook still exits 0 and every other block still runs. The block is skipped when the
envelope carries no agent id.

`writ/analysis/__init__.py` defines its pydantic models (`AnalyzeRequest`, `Finding`,
`AnalyzeResponse`) lazily through a PEP 562 module `__getattr__`, so importing the package
or its stdlib-only submodules (`token_audit`, `token_tree`, `jsonl`) never imports
pydantic, and the hook imports `token_audit` normally. The models are built once under a
lock and cached in the module namespace with their original `__name__`, `__qualname__`
and `__module__`, so every access returns the same class object and JSON schema, repr,
pickling and isinstance checks are unchanged. Rejected: registering a stub `writ.analysis`
package in `sys.modules` inside the hook, which worked but would break silently (no row,
no diagnostic) as soon as a submodule imported anything from the package namespace.

### Immutability: append-only rows, first row wins on read

The hook never rewrites history; a second stop appends a second row. `load_usage_summaries`
keeps the FIRST row per agent_id, even when it is the worse one (`no_transcript` before
`ok`). A later row that differs (ignoring `ts`) is ignored and produces a
`summary_conflict` warning when that agent is audited. Rows match by agent_id alone because
agent ids are unique; a row whose `parent_session` is neither the audited session nor the
parent dispatch's agent still matches and adds `summary_parent_mismatch`.

A row whose `schema` is not 1 (including a missing schema) is skipped before first-row-wins
applies: it neither wins nor conflicts, and a later schema-1 row for the same agent is
used. Each skipped (agent_id, schema) pair is recorded as a
`{kind: "summary_schema_unsupported", agent_id, schema}` warning on the loaded mapping, and
the audit surfaces it only for agents dispatched in the audited tree (the metrics stream
is project-wide, so surfacing every skipped row would report other sessions' agents).

### Audit fallback

`scorecard(..., usage_summaries=None)`: None means no fallback, so efficacy_ab and the
unit tests stay hermetic. The walk always prefers a live transcript. When the file is
missing and an `ok` summary exists, the dispatch is `accounted` with `source: "summary"`,
priced from `model_usage`, and the walk continues into the summary's `child_dispatches`. A
`no_transcript` or `error` summary leaves the dispatch `missing_transcript` with
`summary_status` recorded. The CLI gains `--project` (default
`resolve_project(os.getcwd())`) and always loads the summaries for the audited session id
(the transcript filename stem).

Loading summaries never fails the audit. `resolve_project` and `load_usage_summaries` run
inside their own error handling; on any exception the CLI audits with no summary fallback
and appends `{kind: "usage_summaries_unavailable", error: <exception class name>}` to the
card's warnings. Exit codes are otherwise unchanged (2 on a schema canary failure, 1 on an
unreadable transcript, else 0).

Summary-sourced dispatches do not take part in cross-file `message.id` dedup. A summary
stores per-model token totals, not the message ids behind them, so there is nothing to
check against the seen-id set, and its tokens cannot be deduped against the main thread
or any other file. This is accepted: a cross-file duplicate id was never observed on real
trees (the invariant check exists only as a guard), and a live transcript always wins over
a summary, so the gap applies only after Claude Code has deleted the transcript, when the
alternative is no figure at all.

Tests that invoke `writ token-audit` (`tests/test_token_audit.py`,
`tests/test_token_audit_accounting.py`) point `WRIT_LOG_ROOT` and `WRIT_LOG_PROJECT` at
`tmp_path` through an autouse fixture, so the CLI's summary load never reads the real
metrics stream.

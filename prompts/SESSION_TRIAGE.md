# Session Triage — Layer 1 (haiku)

You are processing ONE Claude Code session transcript and emitting structured findings as JSON. You will be called many times in parallel — be fast, structured, and deterministic.

## Inputs (first two lines of this prompt)

The first two lines give you two **literal absolute paths**:

```
Session transcript to analyze (literal absolute path): /absolute/path/to/session.jsonl
Write your findings JSON to this literal absolute path: /absolute/path/to/findings.json
```

These are plain text values, **not shell variables**. Pass each path directly to the Read and Write tools as a literal string. Never write `$SESSION_PATH`, `$OUTPUT_PATH`, or any `$NAME` in a Bash command — no such environment variable is set, so it expands to nothing and the command fails. You do not need Bash for this task at all; the Read and Write tools are sufficient.

Then:

1. **Read the session transcript** with the Read tool, using the literal path from line 1. It is JSONL — one JSON object per line. If it is larger than ~2000 lines, read it in chunks with the Read tool's `offset`/`limit` (e.g. the first 2000, a middle 2000, and the last 2000 lines) rather than all at once.
   **If a Read fails with a token-limit error** ("File content exceeds maximum allowed tokens"), the transcript has few but very long lines. Do NOT shrink-and-retry the same full read. Instead, page through the whole file with `offset`/`limit` at `limit: 10` lines per Read until you reach the end (dense files have few lines, so this is only a handful of Reads). If even a 10-line chunk errors, halve to 5 and continue from the same offset. You MUST cover the full file this way — never emit a finding saying the transcript was too large or unreadable; that is an extraction failure, not a session finding. Only if paging at `limit: 5` still errors repeatedly should you triage from what you did read, and then emit findings about the session content only.
   Note: an oversized transcript may have been **pre-slimmed** by the runner — long lines truncated, the middle elided, with `...[autodream slimmed/elided ...]...` markers. That is expected; triage what is present and don't treat the markers as session content.
2. **Extract structured findings** per the schema below.
3. **Write the JSON** with the Write tool to the literal output path from line 2 — exactly one JSON object, no prose around it.
4. Print `done` and exit. No commentary.

When present, a **Precomputed session stats** block follows this document at the end of the prompt. Its `turn_count`, `tool_call_count`, `tools_used`, `models_used`, and `compliance_markers` fields are authoritative: copy them verbatim into the output JSON. Do not derive or recount those fields from the transcript. If the block is absent, derive them from the transcript as before.

## What to look for

Quote 1-3 sentences of evidence for every finding. Don't synthesize, don't infer — only report what's literally in the transcript.

**HARD RULE — harness-provided tools are never `fabricated_id`.** A tool named `StructuredOutput` (or `SendMessage`, `Task`) appearing in a `tool_use` but NOT in the `skill_listing` attachment is provided by the workflow/subagent harness, not fabricated. Never flag it. This applies regardless of the transcript's path (slimmed copies lose the `/subagents/workflows/` path hint). Only flag a tool invocation as `fabricated_id` if its `tool_result` is an error saying the tool does not exist. Never emit a finding whose content is that something should NOT be flagged (e.g. "StructuredOutput is harness-provided, not fabricated") — if a rule says don't flag it, write nothing about it at all.

| Category | Signal in transcript |
|---|---|
| `missed_skill` | User invoked a skill manually after Claude did ad-hoc work; Claude did multi-step setup that a known skill (e.g. python-env-management, commit-and-verify) would have automated; Claude said "let me check the help" for a tool that has a skill wrapper. **Exception:** a workflow/subagent transcript running a Bash/curl/API command that its harness handed it verbatim (the agent prompt contains the literal command, e.g. a Caesar `/v1/search` curl recipe) is NOT a missed_skill — it's the harness's intended leaf execution. Do NOT flag a subagent for "should have used the skill" when it was spawned by that skill's own workflow and is executing the recipe it was given. **Second exception, for the "invoked, then did it by hand" case only:** a session that invoked a skill and then did the work by hand is NOT a missed_skill when those actions are the method the skill prescribes (for example a skill that says "drive the CLI through Bash until done" followed by many Bash calls to that CLI). The skill's own text is in the transcript (the `Skill` tool result, or the prompt it injected); compare the actions after the `Skill` call with it. Emit `missed_skill` for this case only when the session switched to a workflow the skill conflicts with, or violated an explicit requirement the skill states (a forbidden tool, a forbidden form), and quote that instruction in the evidence. If the skill's text is not in the transcript, or you cannot name a violated instruction, emit no `missed_skill` for it. This does not change the other signals above: a skill that was never invoked is still judged on the signals listed first. |
| `wrong_skill` | Claude invoked a skill that didn't fit; user corrected ("no use X instead"). |
| `sandbox_friction` | `Operation not permitted`, `dangerouslyDisableSandbox: true` retries, `/tmp` writes failing, permission prompts denied. |
| `memory_miss` | User says "I told you", "we established", "remember", "the same as last time"; Claude re-discovers a workaround that was used in a previous session. |
| `tool_loop` | Same command retried ≥3 times with minor variants (>2 close-but-different curl/grep/find variants in <10 turns). **Marker check:** the retry-budget rules require the agent to emit a literal `RETRY-BUDGET: ...` (or `FETCH-PIVOT: ...`) line in its response text when it stops/pivots. A loop that ends WITH such a marker means the rule worked — severity `low`, and say the marker was present. A loop with NO marker is the real finding — note "no RETRY-BUDGET marker" in `what`. |
| `permission_prompt` | Commands the user repeatedly allowed or repeatedly denied that should be in `.claude/settings.json` allowlist/denylist. |
| `fabricated_id` | Claude quoted a SHA, PR number, line number, function name, or version that wasn't from a just-run command. See the HARD RULE above: tools like `StructuredOutput` that succeed but aren't in `skill_listing` are harness-provided — never flag them. |
| `stop_projection` | "you must be tired", "let's pick this back up", "we should stop", any variant. |
| `drift_after_compaction` | Context summarization happened (look for compaction markers or sudden context loss) and a fact established earlier was forgotten/re-asked. |
| `buggy_code_shipped` | Claude declared something done/working and a later turn shows it broken: a test failure on the "finished" code, the user pasting an error from it. The signal is the premature success claim, NOT the debugging that follows. Normal iterative debugging — try, fail, fix, with no "done"/"working"/"tests pass" claim in between — is NOT this category; emit nothing for it. |

**MORATORIUM — never emit `assumption_unsurfaced`.** Do NOT file any finding about a missing/late ASSUMPTIONS block, regardless of how clearly the transcript shows it. This category is retired (settled 2026-07-03): L2 discards every such finding on arrival, so generating one is pure wasted work. If a session's only notable issue is an unsurfaced/late ASSUMPTIONS block, emit `"findings": []`. Do not re-route it into another category (e.g. `missed_skill`) either.

An empty findings array is a valid result for ANY session where nothing meets the criteria above — not just trivial ones. If a substantive session has no real findings, emit `"findings": []`. Don't pad, and don't manufacture a finding to justify the slot.

## Session facets (pilot fields)

Alongside findings, emit three judgment facets about the session as a whole, plus the instructions list. Same evidence bar as findings: explicit signals only, never inference.

- `underlying_goal` — one line: what the user fundamentally wanted (intent, not activity). If it would just duplicate the top `notable_initiatives` entry, set it to `null`.
- `outcome` — judged from the transcript's end state: `fully_achieved`, `mostly_achieved`, `partially_achieved`, `not_achieved`, or `unclear_from_transcript`. When genuinely ambiguous, use `unclear_from_transcript` — never guess.
- `satisfaction_signals` — **RETIRED 2026-07-28 after its pilot week; always emit all zeros.** Do not attempt to score user sentiment. The field stays in the schema so existing consumers don't hit a missing key, but its value is no longer read. It fired in only 8% of sessions and was wrong in most of those: spot-checking six non-zero cases against their transcripts found one grounded reading, four that scored harness scaffolding as human sentiment (`<task-notification>` blocks, `<teammate-message>` traffic, a bare "Yes", a slash-command invocation), and one on a subagent transcript, which has no human in it to have a feeling. The user role in a transcript carries far more machinery than speech, so sentiment read from it is mostly machinery.
- `instructions_given` — up to 3 one-line paraphrases of explicit STANDING instructions the user stated ("always run tests after edits", "use fish syntax", "never push to main directly"). Standing directives only — not one-off task requests. Empty array when there are none.

For a trivial session (a handful of turns, no substantive work), emit the facets without deliberation: `underlying_goal: null`, `outcome: "unclear_from_transcript"`, all-zero `satisfaction_signals`, empty `instructions_given`.

## Output schema

Write EXACTLY this shape to `OUTPUT_PATH`. JSON only, no markdown fence, no prose.
`compliance_markers` holds counts of `RETRY-BUDGET:`, `FETCH-PIVOT:`, `DELEGATED:`,
and `DIRECT-OK:` marker lines in assistant text (0 when absent — most sessions).
Counting rule (all four markers, same rule): count only lines that BEGIN with the
marker string, in the top-level session's assistant text. Do NOT count markers that
appear inside quoted or fenced blocks, markers quoted from rule files, or markers
inside subagent transcripts — a main-loop message quoting a returned report does not
count. (This line-start rule replaced substring counting for RETRY-BUDGET/FETCH-PIVOT
on 2026-07-20; historical comparisons may shift once.)

```json
{
  "session_path": "/absolute/path/to/session.jsonl",
  "project": "encoded-cwd-folder-name",
  "started_at": "ISO8601 from first message if present, else file mtime",
  "turn_count": 42,
  "tool_call_count": 87,
  "tools_used": ["Bash", "Read", "Write", "Edit"],
  "skills_invoked": ["schedule", "python-env-management"],
  "models_used": ["claude-opus-4-7"],
  "notable_initiatives": ["one-line summary of the main thing the user worked on"],
  "compliance_markers": {"RETRY-BUDGET": 0, "FETCH-PIVOT": 0, "DELEGATED": 0, "DIRECT-OK": 0},
  "underlying_goal": "one line of user intent, or null if it duplicates notable_initiatives",
  "outcome": "fully_achieved|mostly_achieved|partially_achieved|not_achieved|unclear_from_transcript",
  "satisfaction_signals": {"happy": 0, "satisfied": 0, "dissatisfied": 0, "frustrated": 0},
  "instructions_given": ["up to 3 one-line paraphrases of explicit standing instructions"],
  "findings": [
    {
      "category": "missed_skill",
      "severity": "high|medium|low",
      "what": "1-sentence pattern",
      "evidence_excerpt": "verbatim ~200-char quote",
      "proposed_rule": "concrete fix: skill to invoke, allowlist to add, or memory entry to write"
    }
  ]
}
```

If you encounter an error (file unreadable, malformed JSONL), emit:
```json
{"session_path": "...", "error": "what went wrong", "findings": []}
```

Cap findings at 10 per session — pick the highest-severity ones.

## Important

- Do NOT use search-sessions, grep across other sessions, or read any file besides the session transcript path you were given (you have just this session's scope).
- Do NOT write anywhere except the output path you were given.
- Do NOT update MEMORY.md, CLAUDE.md, or skills — Layer 2 owns aggregation; you only emit signal.
- Be fast. Aim for <30s per session.

**`skills_invoked` and `skills_authored` come from the precomputed stats block, never from your own reading.** Both are counted mechanically by the runner and appear in the "Precomputed session stats" section below the schema; copy them across verbatim, together with `skills_invoked_count` and `skills_invoked_counts`. Do not infer a skill invocation from a tool call that writes or edits a skill file: that creates or changes a skill, it never runs one. The runner overwrites these four fields from the sidecar after you finish, and removes them when the sidecar could not measure them.

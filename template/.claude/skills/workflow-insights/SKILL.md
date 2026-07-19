---
name: workflow-insights
description: "Generate a Claude Code usage insights report from session history — token economics, context health, friction patterns, experiment verdicts. Trigger on: /workflow-insights, 'insights', 'usage report', 'session insights'. Output feeds /workflow-retro Step 1."
allowed-tools: Read Write Edit Bash Glob
---

# Claude Code Insights

Analyze all Claude Code sessions and generate a report covering:
- Token economics: cost by model, by tool, by skill/agent, context-size distribution
- Context load: what contributes to context growth (skills, hooks, always-loaded files)
- Friction patterns: antipatterns, errors, hook blocks
- Experiment verdicts: check active hypotheses from the tooling ledger
- Recommendations: concrete changes ranked by impact

The engine is `librarian/tools/cartographer/parser.py` (canonical since 2026-07-17).
`~/.claude/scripts/insights.py` is a forwarding shim to it — same flags either way.

## Steps

1. Load the `insights-analysis` ref (`~/.claude/refs/insights-analysis.md`) — use
   this as the interpretation framework when reviewing the generated report with the user.

2. Check that `ANTHROPIC_API_KEY` is set in the environment (or `~/.claude/.env` — the parser
   falls back to it). If neither, tell the user and offer `--dry-run` (keyless stats only).

3. Run the insights engine:
   ```
   python3 ~/.claude/scripts/insights.py --output ~/.claude/usage-data/report.html
   ```
   For dry-run: `python3 ~/.claude/scripts/insights.py --dry-run`

4. Once complete (non-dry-run), open the report:
   ```
   open ~/.claude/usage-data/report.html
   ```

5. **Summary** — present the headline numbers:
   - Sessions analyzed, date range, messages
   - % of usage over 150k context (the top cost lever)
   - Cache hit rate and savings
   - Subagent share

6. **Model breakdown** — from `model_distribution`, report cost-weighted usage per model.
   Flag if expensive models (opus) are used on routine tasks, or cheap models on
   judgment-dense work. Compare to the model-pairing ref (`~/.claude/refs/models.md`).

7. **Tool & skill economics** — from `top_tools`, `skill_usage_pct`, `skill_invocations`:
   - Which tools dominate (Read/Edit/Bash) and their relative share
   - Which skills consume the most context (by `skill_usage_pct` — cost-weighted)
   - Skill invocation frequency vs cost share (high-freq/low-cost = efficient; low-freq/high-cost = bloated)
   - Agent spawns: count, model used, share of total spend
   - Flag skills/agents that load disproportionate context per invocation

   **Coverage diff** — `skill_invocations` only shows what ran. Also report what never
   did, by diffing invoked names against skills on disk. Pass the `skill_invocations`
   dict from the step-3 run (do not re-run the parser):

   ```
   python3 - <<'PY'
   import json,os,glob
   si = json.loads(os.environ['SKILL_INVOCATIONS'])   # from the step-3 output
   g={os.path.basename(p.rstrip('/')) for p in glob.glob(os.path.expanduser('~/.claude/skills/*/'))}
   r={}
   for p in glob.glob(os.path.expanduser('~/workspace/*/.claude/skills/*/')):
       n=os.path.basename(p.rstrip('/'))
       r.setdefault(n,[]).append(p.split('/workspace/')[1].split('/')[0])
   print('GLOBAL NEVER INVOKED:',sorted(g-set(si)))
   print('REPO NEVER INVOKED:',sorted(f'{s} ({",".join(r[s])})' for s in set(r)-set(si)))
   print('INVOKED, NOT ON DISK:',sorted(set(si)-(g|set(r))))
   PY
   ```

   Read the three lists with these caveats — do NOT report raw counts as fact:

   - **Zero invocations ≠ unused.** `skill_invocations` merges two sources
     (`parser.py:307`): typed `/slash` text, plus `Skill` tool calls. That covers both
     direct and auto-triggered use, but a skill whose logic was inlined by hand — the work
     done without ever invoking it — still reads as zero. Treat the zero set as a
     description-quality signal, not a delete list.
   - **"Invoked, not on disk" is mostly noise**: built-in CLI commands (`/clear`,
     `/config`, `/compact`), bare paths (`/private`, `/tmp`), and typos. Two things there
     are real and worth flagging: a **typo'd invocation** that silently did nothing (e.g.
     `design-inistiative`), and a **name that looks like a skill you meant to have**.
   - Repo skills are only reachable from their own repo. Weight a repo skill's zero count
     against how often you work in that repo before calling it dead.

   Report the zero-invocation set as a **candidate list for description review**
   (`skill-creator` has description-optimization), not as dead weight. Recommend deletion
   only where a skill is both never invoked AND superseded by a named alternative.

8. **Context load analysis** — what contributes to context growth:
   - Always-loaded files (CLAUDE.md chain, rules, MEMORY.md) — estimate token count
   - Per-skill context additions (skill prompt size + files read during skill)
   - Hook overhead (number of hooks × fire frequency)
   - Recommend: which skills/hooks/always-loaded content to slim or lazy-load

9. **Friction patterns** — from tool errors, bash antipatterns, hook blocks:
   - Error types and frequency
   - Bash antipatterns per session (shell used where dedicated tools exist)
   - Hook blocks (PreToolUse blocks, Stop blocks) — useful vs. false-positive
   - read:edit ratio (sessions editing without reading first)
   - Long sessions without planning structure

10. **Experiment check** — read `~/workspace/guacamayo/.claude/docs/tooling-ledger.md` and
    find rows with status `hypothesis` that have a typed Metric (not `—`). For each, check
    the session data against the metric:
    - `absence:<signal>` — search sessions for the signal; 0 occurrences = confirmed
    - `count-drop:<signal>` — count occurrences per session, compare to threshold
    - `presence:<signal>` — search for the signal; any occurrence = confirmed
    - `ratio:<metric>` — compute from session stats

    Also check legacy hypothesis rows (Metric = `—`) if their status text contains a
    checkable signal (e.g., ">150k share", "dispatch correctly").

    Report a table:
    ```
    | Experiment | Metric | Verdict | Evidence |
    ```
    Verdicts: `confirmed` (met threshold), `trending` (improving but not met),
    `inconclusive` (insufficient data), `failed` (metric violated).

    Do NOT update the ledger — that's /retro's job. Just surface the verdicts.

11. **Recommendations** — synthesize findings into 3-5 ranked recommendations:
    ```
    ### R<N>: <one-line recommendation>
    **Impact**: <which metric this moves and by how much>
    **Mechanism**: <what to change — hook, skill, setting, workflow>
    **Metric**: <how to measure success — typed metric for the ledger>
    ```
    Rank by cost-weighted impact. The single biggest lever goes first.

12. **Persist summary** — write the machine-readable output to
    `~/workspace/guacamayo/.claude/docs/insights-summary.md` (overwrite each run):

    ```markdown
    # Insights Summary — [date]

    ## Numbers
    [key metrics as a table]

    ## Model Distribution
    [model: message count, cost-weight share]

    ## Skill Economics
    [skill: invocations, cost-weight share, context contribution]

    ## Skill Coverage
    [never-explicitly-invoked: global list, repo list (with repo names)]
    [typo'd/unresolved invocations worth fixing]

    ## Experiment Verdicts
    [the experiment table from step 10]

    ## Recommendations
    [the ranked recommendations from step 11]

    ## Trends
    [comparison to previous run if prior summary exists — what improved, what worsened]
    ```

    This file is what `/retro` reads as an observation source (Step 1.1 in retro).

## Options

Arguments pass through to the engine:

- `--dry-run` — extract stats only, no API call, print JSON to stdout
- `--model claude-sonnet-5` — report-generation model
- `--output <path>` — report path (default: `~/.claude/usage-data/report.html`)
- `--sessions-dir <path>` — session-note markdown files (default `~/.claude/sessions`)
- `--projects-dir <path>` — JSONL location (default `~/.claude/projects`)

Cartographer-only subcommands (run from librarian): `--cron`, `--migrate`, `--compare`, `--enrich`.

# MANDATORY PRACTICES — every dispatched agent, every time

⛔ **Owner standing instruction 2026-09-23: "All these best practices must be durably recorded for all future to
must use."** This file is the ONE place they live. Every brief in this directory points here, every dispatch spec is
rendered by `make_dispatch_specs.py` (never hand-written in a scratchpad), and `check_practices.py` fails when a brief
or a rendered spec drops one. A practice that is only in a transcript or a scratchpad file is FORGOTTEN — the wave-58
dispatch still depended on `GATE-WAIT.txt` and a tail file living in one session's scratchpad.

Each rule carries its reason and its measurement; do not drop a rule because its reason looks stale — re-measure.

## All roles

| # | Practice | Why (measured) |
|---|---|---|
| P1 | **Opus 5.5 via the `opus` alias** (`CLAUDE_CODE_SUBAGENT_MODEL=opus`, `model: 'opus'` on every agent). Never a dated id. | Owner 2026-09-22 (DEVLOG 1635). |
| P2 | **Never end your turn while a background job runs.** Start it to a log, then BLOCK: `timeout 580 bash -c 'tail -n +1 -f <log> \| grep -m1 "<verdict>"'`, re-issued until the verdict prints. push-main: append `echo PUSH-MAIN-EXIT=$?` and block on it. | Wave 45: five implementers + a lander returned "gate PENDING", every gate killed. |
| P3 | **Graceful STOP.** Before each new step check `{SCRATCH}\STOP`; if present: checkpoint-commit, STATUS.md NEXT, report, return SPLIT / landed=false. Never start a build or gate once STOP exists (a lander that has STARTED push-main finishes it). | Owner 2026-09-22: no job may be killed by a quota limit. |
| P4 | **Checkpoint to disk**: WIP commit after every mechanism/step + `STATUS.md` (DONE / NEXT / BLOCKED / GATE / batch paths / codes). Never `git stash` (shared across worktrees) — and never `git rebase --autostash` / `git pull --autostash`, which stash implicitly (train 64, 2026-09-25). | Session kills cost at most one step. |
| P5 | **Turn caps**: read-only 160, implementer 220, one landing per lander transcript. At the cap: checkpoint and SPLIT, never extend. | tokens ≈ 0.115·T + 0.00031·T² (n = 239). |
| P6 | **Start from the code sites** — the note's file:line, or `python scripts/spec/where.py <clause> [rule]` (every rule is cited in code, so the citations ARE the index). Do not re-survey a subsystem. | Waves 45–57: grep/find/sed/Read = **46 %** of all implementer tokens — the largest single cost. |
| P7 | **Every lead you report carries its repro path and its code site (file:line)**, so the registrar and the next implementer do not re-discover them. | The same fact was being found three times: implementer → registrar re-probe → implementer re-probe. |
| P8 | **Citations through `cite.py --check`**; ids and diagnostic codes only from the orchestrator's allocation; reports at `{SCRATCH}\reports\<wave-slug>-<lead>-report.md` (wave-prefixed). | Inherited-citation defects (CA10); five id collisions in one day; train 48 found reports overwritten. |
| P9 | **`python scripts/semgrep/verify.py` may not increase any count.** | Train 57 dropped PB999 for +20 BigInteger hits nobody reported. |
| P10 | **Apply the public skills for your role** (table below): read each named `SKILL.md` / agent file from the local clone `E:\claude-skills` (https://github.com/BrentRector/claude-skills) at the step it names. The project's own skill and this file WIN on conflict; the public skill supplies the method, never a looser bar. | Owner 2026-09-24: "apply all of our new relevant skills" — the generalized bar was published but no dispatched agent read it. |
| P11 | **Ask the drift rules before editing**: `python scripts/spec/drift_rules.py <files>` lists the drift tests that govern them (generated from their `<summary>`s; `docs/DRIFT_RULES.md`). Honor every SPECIFIC rule; a new `*DriftTests` class states its rule in a `<summary>` (the index reports the ones that don't). | Owner 2026-09-25: 216 drift tests, 7 named in any skill — agents learned each rule only by tripping it at the gate (e.g. TestRepoDriftTests on a new test the same day). |
| P12 | **A hook block is the rule speaking — comply, never route around it.** `scripts/hooks/forbidden_commands.py` (every Bash/PowerShell call, inside subagents too) blocks `git stash`/`--autostash`, a direct push to main, backslash escapes in a heredoc body, and filtered `dotnet test` runs with a property-less `~X` term or unredirected output; the read-only roles' `readonly_repo.py` blocks any Write/Edit inside a git tree. Wrapping the blocked command in a script file to dodge the hook is the same violation. | Owner 2026-09-25 (tooling rec. 2): each rule was prose in a skill and was broken anyway — a shared-stash pop (PB713), `--autostash` by a lander, heredoc mangling in six sessions. Self-tests run in CI `audits`. |
| P13 | **Navigate C# with the LSP tool before grep**: `goToDefinition`, `findReferences`, `incomingCalls`, `workspaceSymbol` on the `.cs` file (the `csharp-lsp` plugin + `csharp-ls`). Grep stays right for text, COBOL, docs and generated files. | Tooling rec. 7: agents spent ~46 % of their tokens on grep/read orientation; a reference query returns the exact sites instead of file dumps. |

## Public skills by role (P10) — `E:\claude-skills\skills\<name>\SKILL.md`, `E:\claude-skills\agents\<name>.md`

| Role | Read before work | Apply at |
|---|---|---|
| Implementer / finisher | `engineering-standards`, `dotnet-engineering`, `spec-oracle` (the project's `spec-lookup` wins) | design + code; the root-cause and re-architecture rules are CLAUDE.md rules 4–5 in generic form |
| Implementer / finisher | `variant-analysis`, `roslyn-analysis` | the SIBLING SWEEP after each defect is confirmed — name the mechanism, query every arm and every place the rule is written; report the sweep so a zero is evidence |
| Implementer / finisher | agents `pr-test-analyzer`, `silent-failure-hunter`, `comment-analyzer`, `type-design-analyzer` (the last only when the diff adds or reshapes a type) | SELF-REVIEW of your own diff before the report: run each file as a checklist; fix what it finds or list it in the report with its failure scenario |
| Registrar | `variant-analysis` | clustering leads by mechanism (R3) |
| Adjudicator / refuter | `spec-compliance-audit`, `spec-oracle` | verdict vocabulary, checked citations, the refuter on every closing verdict |
| Lander | `test-gate` (the project's `gate` wins), agent `silent-failure-hunter` | reading every leg's verdict line; a filter that matched nothing is a red |
| Reviewer | `review` (the project's `review` wins), all four agents | the four dimensions + adversarial verification |
| Orchestrator | `agent-fleet` (this skill's base), `claude-cloud-sessions` | dispatch, budget, cloud billing |

## Implementer / finisher

| # | Practice | Why |
|---|---|---|
| I1 | Gate = own tests + `~Drift\|~EditionGate` + Unit, **always `-Priority BelowNormal`**; a shared seam (.g4, MOVE, reference resolver, EC emitter) adds `~CorpusRunner\|~Nist`. **A change that REJECTS source it used to accept (a new diagnostic, a tightened rule) also adds `~VersionMatrix`** — the construct samples in constructs.json compile at every edition. | Lander's whole-assembly leg went 9.6 → 30.6 min when implementers competed at Normal. |
| I2 | **Never run the whole Conformance assembly.** | Seventeen implementers running it tripled the lander's gate time. |
| I3 | Re-probe every note on your own build first; a non-reproducing note is DISCHARGED with evidence. | Wave 42: three stale notes. |
| I4 | One positive golden at the introducing edition + one negative below it; parser + emitter + golden + manifest in one commit. | Owner 2026-09-13 lever 3. |
| I5 | Flip `status` + write `closes_rows` in the landing commit; `work.py check`; no lists anywhere. | CLAUDE.md rule 8. |
| I6 | Report ≤ 60 lines per `implementer-report-template.md`. | Owner 2026-09-13 lever 4. |
| I7 | **Every golden and negative you ADD runs BY NAME at your gate** (`DisplayName~<name>` term, or the corpus leg) and the report quotes its pass line; `Manifest_CoversEveryProgram` alone proves registration, not execution. | Train 60: a w59d negative shipped with no `.err` because its implementer's gate ran only the manifest test; the lander's whole-assembly gate caught it. |

## Lander (train)

| # | Practice | Why |
|---|---|---|
| L1 | 4–6 clusters per landing (target 5); one commit per cluster; one DEVLOG entry; one push. | 10.4 M/cluster at k = 1 vs 5.1 M at k = 5. |
| L2 | Gate = the **WHOLE Conformance assembly, unfiltered** + Unit + Characterization, at **Normal** priority, in the lander's worktree. | Trains 39–41 went red on CI's `rest` shard behind green union-of-filters gates. |
| L3 | **Pipelined**: dispatched while the previous train is still in CI; merge + gate on current origin/main; before push-main BLOCK until the previous head is an ancestor of origin/main, rebase, and re-gate ONLY if the rebase had conflicts outside docs/kb/DEVLOG. | Train 50 waited 44 min for train 49 when serial. |
| L4 | The compiled-program cache (PB985) makes a re-gate after a test-only fix skip recompilation — never clear it to "be safe". | Cold re-gate 22m53s → warm 1m18s. |
| L5 | Land ONLY via `bash scripts/push-main.sh` (required `ci-gate`); read the CI run; a red is a blocking finding landed alone. | Main red 29 h across 16 runs (PB796). |
| L6 | Verdict batches re-applied with `record_verdicts.py` on the merged tree, never merged as JSON hunks; check the GAP delta. | Per-record drops. |
| L7 | `git add -A -- . ":!.claude/settings.local.json"` then `git reset -q -- STATUS.md`. | A checkpoint reached main (2026-09-02). |
| L8 | DEVLOG number read after the FINAL fetch+rebase; on a non-fast-forward, rebase and renumber. | Parallel landers. |
| L9 | **Review the train before push-main** (lander-train-brief step 5b): the `review` skill's full-code pass over `git diff origin/main...HEAD`; a confirmed correctness finding DROPS its cluster. | Owner 2026-09-25 (tooling rec. 8); `/code-review` is interactive-only, so the owner runs `/code-review ultra` on big batches. |

## Registrar

| # | Practice | Why |
|---|---|---|
| R1 | Grep every lead against `kb/Work/` first; extend, never duplicate; never edit a note an in-flight implementer holds. | Duplicate notes. |
| R2 | Re-probe on your own build ONLY when the lead lacks a runnable repro + code site (P7); otherwise run the given repro once and record the result. | Triple probing. |
| R3 | One note per mechanism (cluster by root cause); each note records its CODE SITES (file:line) for the implementer. | Owner lever 1; P6. |

## Battery

| # | Practice | Why |
|---|---|---|
| B1 | In a DETACHED worktree cut at the batch head, never on main; long legs one at a time; Normal priority. | A battery on main froze the lander ~45 min. |
| B2 | Attribute every red by name; differential flips per case; re-baseline only when the standard licenses it. | Verdict-evidence invariant. |

## Orchestrator

| # | Practice | Why |
|---|---|---|
| O1 | Dispatch specs are RENDERED: `python .claude/skills/workstream/make_dispatch_specs.py <groups.json>`; then `python .claude/skills/workstream/check_practices.py <specs…>` must pass before the Workflow call. | This file. |
| O2 | Fill implementer slots one group per subsystem; land finished work first; one battery per landing batch; ledger refresh after every GAP-moving landing. | SKILL.md §2–§3. |
| O3 | Read the quota meter (Claude in Chrome) before every dispatch; obey the day's allowance and the ~85 % session STOP. | Owner 2026-09-12/20/23. |
| O4 | **Fleets run through the Workflow tool — a STANDING owner opt-in (2026-09-25); never ask per session.** Every `agent()` names its role's `agentType` from `.claude/agents/`: `cobol-implementer` (Opus, high, 220 turns) · `cobol-lander` (Opus, high) · `cobol-refuter` (Opus, xhigh, read-only by hook) · `cobol-adjudicator` (Opus, high, read-only by hook; also probes/validators) · `cobol-clerk` (Sonnet, medium; mechanical chores only). Each carries a 1-hour prompt cache. | Tooling recs. 1/3/4/9: reports stay out of the orchestrator's context; a 5-minute cache re-read every gate-blocked agent's context uncached. Roll a role back to `xhigh` if its refuter overturn rate rises. |
| O5 | **Measure cost per role from telemetry, not by hand**: `python scripts/telemetry/usage_report.py [day…]` (the local `otlp_sink.py` records Claude Code's OTLP export; enabled per machine in `.claude/settings.local.json`). The claude.ai meter stays the pacing authority (O3). | Tooling rec. 5: the hand-kept usage tally could not attribute cost to a role. |
| O6 | **Act on the session-start TOOLING block** (`scripts/hooks/tooling_check.py`, printed by the SessionStart hook): every `ASK-OWNER` line becomes one AskUserQuestion at the start of the session — never a silent skip; `REPAIRED` lines need nothing. After the owner's `/skill-doctor` run, prune what it flags and `touch ~/.claude/cobolsharp-skill-doctor.stamp`. | Owner 2026-09-25: "It should not require manual intervention to use these. If my explicit permission … is required, automatic use … should trigger a query to me, not silently failure to use it." |
| O7 | **Owner-only, billed or interactive steps are ASKED at their trigger, never skipped**: at every battery close over a multi-train batch, ask the owner whether to run `/code-review ultra` on that range; after editing any public skill (`E:\claude-skills`), run its eval cases (`claude plugin eval E:\claude-skills --case <glob>`, see `evals/README.md`) and do not push it red. | R49 recs. 6 and 8; the same owner instruction as O6. |

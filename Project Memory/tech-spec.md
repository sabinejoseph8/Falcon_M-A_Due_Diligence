# Tech Spec: Project Falcon

**Status:** Agreed, version 1.14 (October 19, 2026: exact grading rule in `/evaluate`, positives row, one status per finding, Checkpoint 1 printed in chat).

This file holds the technical decisions and system patterns. It describes the system as built so far, and flags the risks that matter most.

## Architecture overview

Project Falcon runs inside Claude Code on the operator's computer. There is no server and no application code. The "program" is a set of plain-text files that Claude Code reads.

| Part | What it is | Where it lives |
|---|---|---|
| **Lead agent (Agent Core)** | Instructions for the main Claude Code session: the Plan, Act, Observe loop, checkpoints, report template, rubrics and guardrails | `CLAUDE.md` |
| **Specialist subagents** | Four source specialists plus a citation verifier, each with its own instructions and tool list | `.claude/agents/*.md` |
| **Commands** | One-word entry points for the operator | `.claude/commands/*.md` |
| **Guardrails** | Permission rules that Claude Code enforces (not just instructions) | `.claude/settings.json` |
| **Targets** | One folder per fictional target. Each holds its sources (one folder per source type, standing in for SEC search, a news feed, a litigation database and financial data), its answer key and a checksum manifest | `targets/<target>/data/`, `targets/<target>/evaluation/`, `targets/<target>/data_manifest.json` |
| **Working memory** | Plan, findings register, open questions, key metrics, run log, unedited analyst reports | `memory/` |
| **Report pipeline** | Markdown report, converted to a styled web page and a PDF | `output/`, `templates/report-style.css` |
| **Evaluation** | Answer key of planted issues per target and a grading command | `targets/<target>/evaluation/`, `/evaluate` |
| **Automated checks** | Tests for each build phase, plus a run checker | `tests/`, `/run-tests` |
| **Archive** | Past runs and their scorecards, moved aside by `/reset-memory` | `runs/` |
| **Portfolio** | README, diagram, run guide, sample run, case study, planning files | `README.md`, `docs/`, `examples/`, `Project Memory/` |

```
Operator --/diligence--> Lead agent (CLAUDE.md) --task--> 4 specialists in parallel (read-only)
                              |    ^                                |
                              |    +---------- findings ------------+
                              v
                        memory/ (register, run log, reports) --> citation-verifier --> output/ report
                              ^
               Human checkpoints 1, 2, 3 (operator replies in the conversation)
```

## Technology choices

| Choice | Reason |
|---|---|
| Claude Code (terminal or desktop app) | Built-in subagents, commands and enforceable permissions, with no code to write or host |
| Markdown for agents, commands, memory and the report | Readable by anyone, easy to review and version |
| CSV for financial data | Opens in Excel, easy to check by hand |
| JSON for permission settings | The format Claude Code requires |
| Python 3, standard library only, for automated checks | Nothing to install on Mac or Linux; deterministic results |
| Pandoc and a headless browser for the PDF (optional) | Best-looking output when available; the web page plus "Print, then Save as PDF" works everywhere. On the builder's Mac, headless Google Chrome (`--headless=new --print-to-pdf`) made the PDF with nothing installed |
| SVG for the architecture diagram, exported to PNG and PDF | Sharp at any size and easy to edit |
| Git and GitHub | Version history and the public portfolio |

## Data model

| Entity | Key fields |
|---|---|
| **Deal brief** | Buyer, target, price, shares, valuation basis, the six committee questions, dates |
| **Source document** | Type (folder), file name, date; every document is labeled fictional |
| **Finding** | ID (`SEC-`, `NEWS-`, `LIT-`, `FIN-` + 2 digits), one-line finding, evidence, source (file and section, row or docket date), severity, confidence, claim type (news), deal impact, cross-check, status, iteration |
| **Cross-source finding** | ID (`X-` + 2 digits), the finding, the IDs it is built from, severity, confidence, status, recommended action |
| **Conflict** | ID (`C` + number), side A, side B, status |
| **Follow-up** | ID (`F` + number), assigned specialist, question, reason |
| **Run target** | The target folder name, one line in `memory/target.txt`, written by `/diligence` and archived with the run |
| **Run log entry** | Time, step, what happened, decision or checkpoint |
| **Verification verdict** | Finding ID, verdict (Verified, Partially verified, Not supported), what was checked, correction |
| **Planted issue (answer key)** | ID (`P` + 2 digits), issue, where the evidence is, expected severity, cross-source flag |
| **Scorecard row** | Planted issue ID, result (Found, Partially found, Missed), matching finding IDs. The planted-positives row: its answer key ID, result (Present, Partly present, Absent), missing positives |

**Allowed values:** severity Critical, High, Medium, Low (plus Positive for strengths); confidence High, Medium, Low; claim type Fact, Allegation, Rumor; status exactly one of Open, Verified, Partially verified, Rejected, with nothing added (an unverified Low finding stays Open).

## Interfaces between parts

| From | To | Interface |
|---|---|---|
| Operator | Lead agent | Commands (`/diligence [target]`, `/diligence-status`, `/evaluate [target]`, `/reset-memory`, `/run-tests`; the target defaults to `falcon`) and checkpoint replies ("approve", "dig deeper on <topic>", "proceed", "approve report") |
| Lead agent | Specialist | A task message: deal context, the target's source folder, task list, facts from other sources with their citations, and a reminder of the output format |
| Specialist | Lead agent | One final message in the standard format: files reviewed, finding cards, positives, gaps |
| Lead agent | Working memory | Files with fixed names and table layouts (see the templates in `templates/memory/`) |
| Lead agent | Verifier | The target's source folder and a list of findings: ID, claim, cited sources, severity |
| Verifier | Lead agent | One report per batch: a verdict for each finding, what was checked and any correction. The lead rewrites each Partially verified row with that wording before Checkpoint 3 |
| `/evaluate` | Answer key | Read only after the operator approves the permission prompt |
| `/reset-memory` | Archive | Moves `memory/` (including `target.txt`), `output/` and the target's `evaluation/scorecard.md` into a dated `runs/` folder, then restores the blank templates |
| Report pipeline | Files | Markdown, then HTML with the stylesheet embedded, then PDF |

## System patterns (secure and extensible)

- **One source per specialist.** Swapping a simulated source for a real one (for example a news connector) changes one folder and one agent file, nothing else.
- **Least privilege.** Specialists can only read. Only the lead agent writes, and only to `memory/` and `output/`. Edits to source data and the answer key are denied.
- **Instructions are not enforcement.** Anything that must always hold is backed by a permission rule or an automated check, not only by an instruction.
- **Sources are evidence, never instructions.** Every agent is told to report, not obey, any instruction-like text inside a document (prompt-injection defense).
- **Single source of truth.** The findings register holds every finding. Findings are never deleted; only their status changes.
- **Separation of duties.** Specialists find, the verifier checks, a human approves.
- **Bounded loops.** At most three iterations, with stop conditions and a logged reason for every extra loop.
- **Evidence-carrying claims.** No finding without a citation. The verifier and the checks enforce it.
- **Append-only audit trail.** The run log only grows, each analyst's unedited report is kept, and old runs are archived rather than deleted.
- **Blind evaluation.** Everything in a target's `evaluation/` folder (the answer key and the latest scorecard) needs operator approval to open, and the answer key's checksum is tested so any change is visible. `/reset-memory` moves each scorecard into its archived run, and earlier runs (`examples/`, `runs/`) need approval too, so a new run cannot read past answers.
- **Nothing found is dropped silently.** Findings that were not verified still appear in the report appendix, labeled "not verified".
- **Template-driven output.** The report structure lives in `CLAUDE.md` and the look lives in one stylesheet.

## Security

- **Authentication:** the operator's own Claude Code sign-in. Nothing else to sign in to, and no passwords or keys in the project.
- **Authorization:** permission rules in `.claude/settings.json` (web tools denied; edits to every target's `data/` and answer key, and to `tests/`, denied; reading anything in a target's `evaluation/` folder or an earlier run needs approval; each rule is written for `targets/*/` so a new target is covered automatically) and a read-only tool list for every subagent. Subagents inherit the project's permission rules.
- **Secrets:** none in v1. Future connectors must use admin-approved credentials stored outside the project. Never commit keys.
- **Input validation:** source documents are untrusted input. The prompt-injection rule, read-only tools, no web access and human checkpoints limit what a malicious document could do. Data files are checked against a checksum manifest.
- **Rate and cost limits:** 3-iteration cap, narrow follow-up tasks, small sources. The full sample run used about 1.95 million subagent tokens across 10 subagent runs (4 analysts, 2 follow-ups, 4 verifiers) and took 69 minutes from the approved plan to sign-off. Iteration 1 alone used about 0.76 million tokens and 26 minutes.
- **Real client data (future only):** use an Enterprise plan, request zero data retention for Claude Code, connect internal systems through admin-approved read-only connectors, and get compliance sign-off first.

## Hosting, deployment and configuration

- **Runs locally.** Clone or download the project, open the folder in Claude Code, type `/diligence` (or `/diligence <target>`).
- **Configuration:** `.claude/settings.json` is shared and committed. Personal overrides go in `.claude/settings.local.json`, which is not committed.
- **Publishing:** the GitHub repository `sabinejoseph8/Falcon_M-A_Due_Diligence` holds the README, diagram, sample run and planning files, and stays private until the owner makes it public. A `.gitignore` keeps `interview-notes.md` and Python caches out. The Project Memory website is a private claude.ai page until it is shared.
- **Optional tools:** Python 3 for the checks and for `tools/md2html.py`, the report converter (standard library only); Google Chrome in headless mode (`--headless=new --print-to-pdf`) for the PDF. No pandoc or other installs needed, by the owner's choice.

## Testing approach

- **Automated checks** (`python3 tests/run_all.py`, or `/run-tests`), grouped by build phase:
  - Phase 1 (`test_phase1_config.py`): agents valid and read-only, commands present and not shadowing built-ins, guardrail rules present (including approval to read a target's `evaluation/` folder or an earlier run, and `/reset-memory` archiving the scorecard and the run's target), `CLAUDE.md`, `/diligence`, `/evaluate` and the subagents naming no single target, checkpoints and loop cap in `CLAUDE.md`, each checkpoint printing its content in chat before the question and logging that it was shown, the verifier counting its summary from its table, and `tools/md2html.py` converting the report's Markdown (raw `<div>` passthrough, nested lists, tables, embedded stylesheet).
  - Phase 2 (`test_phase2_data.py`), for every folder in `targets/` with a `data_manifest.json`: financial statements tie out (quarters against the income statement's years and half-years), documents labeled fictional, deal brief and README present, docket files present, answer key IDs complete with no gaps (exact counts pinned in the optional `checks.json`), source data unchanged (checksums). `python3 tests/run_all.py --write-manifest [--target <name>]` writes each target's manifest.
  - Phase 3 (`test_phase3_run.py`): the run's target (from `memory/target.txt`, or `falcon` for runs saved before Phase 7) exists, a run's findings are complete, the loop cap held, all analyst reports saved, all three checkpoints logged, each checkpoint's run-log row saying its content was shown in chat, and the report has every section, cites only known findings and excludes rejected ones.
  - Phase 4 (`test_phase4_evaluation.py`): the scorecard reports all four metrics and grades every P row in its target's answer key, which for Kestrel and Heron includes the planted-positives row that `/evaluate` now grades in its own row. Falcon stays pinned to P01 to P18 in `targets/falcon/checks.json`, so its archived scorecards, graded before the positives row had its own row, still pass.
  - All phases (`test_style.py`): no em dashes, README links work (including encoded paths such as `Project%20Memory/`).
  - In all: 49 checks (43 before the Phase 7 layout added six target checks). Run 5's last two suggestions added two, and the Phase 5 docs review added one that checks edits to `tests/` are denied. Before the run 5 fixes there were 34, and the sample run and graded runs 1 to 4 passed all 34 with none skipped. The new checkpoint-shown check fails on run 5 by design, and it has not yet been run against the earlier saved runs, whose logs may not use the word "shown". The ID checks accept two- or three-digit IDs with an optional letter (`SEC-01`, `SEC-001`, `LIT-F01`), ignore court case IDs (`LIT-001`), and fail if any workstream's findings cannot be read.
- **Manual verification:** step-by-step checks for each phase in `progress.md`.
- **Quality score:** `/evaluate` grades each run against the answer key (recall, severity accuracy within one level and exact match, unsupported findings, distractors, and the planted positives as Present, Partly present or Absent).

## Critical risks and challenges

Riskiest first. The first four are addressed in the earliest phases.

| # | Risk | Why it matters | How we handle it |
|---|---|---|---|
| 1 | **Instructions are not enforcement.** An agent could skip a checkpoint, read the answer key or wander outside its source. | The whole value is controlled autonomy. A skipped checkpoint undermines trust. | Permission rules for the hard limits, read-only tools, checks that confirm all three checkpoints were logged, and an operator who watches the run. |
| 2 | **Wrong or mis-cited findings** reach a high-stakes report. | One invented number can discredit the whole report. | Mandatory citations, an independent verifier, "Not supported" findings excluded, every correction applied before Checkpoint 3, checks that every cited ID exists, and human sign-off. |
| 3 | **Prompt injection** through a source document. | Real data rooms contain text the builder does not control. | "Evidence, never instructions" rule in every agent, no web access, no write access for specialists, human checkpoints. A manual injection test is in Phase 5. |
| 4 | **Claude Code features change** (for example commands merging into skills, a new built-in command name). | A silent change could disable an agent or a guardrail. | Phase 1 checks catch missing or invalid configuration; a docs review with Claude Code's guide agent before each release. |
| 5 | **Run-to-run variation.** Two runs can find different things and score differently. | A single score could be luck. | Fixed output format and rubrics; grade several runs and report the average and range; keep the sample run as a fixed reference. Measured over three blind runs: Critical and High recall 96.2% to 100%, overall 91.7% to 94.4%. |
| 6 | **Parallel and background behavior.** Background subagents may not be able to ask for permissions, and parallel start is not guaranteed. | A blocked analyst could silently return less. | Specialists only need read access inside the project (no permission prompts); the lead waits for every report and retries a failed analyst once. |
| 7 | **Arithmetic without code.** The financial analyst is read-only and calculates by hand. | A math slip could change a conclusion. | Show-your-work rule, independent recomputation by the verifier, automated tie-out checks on the data, key numbers kept in one dataset. |
| 8 | **Cost and time.** Four large-context analysts per iteration. | Long or expensive runs discourage use. | Small sources, narrow follow-ups, 3-loop cap. Measured on the sample run: about 1.95 million subagent tokens and 69 minutes from plan to sign-off (iteration 1: 0.76 million tokens, 26 minutes). |
| 9 | **Missing tools on the operator's computer** (no Python, no PDF tool). | Checks or PDFs would fail. | Standard-library-only checks, the HTML fallback for PDFs, and manual verification steps for every phase. |
| 10 | **Simulated data is easier than reality**, and agents could be tuned to the planted issues. | The score could overstate real-world performance. | Distractors in the data, a blind answer key, and (future) a second fictional target that the instructions were never tuned on. The first test run was only partly blind (the lead agent ran in the session that built the data). The fully blind run in a fresh session scored 96.2% recall on Critical and High issues and 94.4% overall, close to the sample run, which suggests the first score was not inflated. A second fictional target is still needed to test generalization. |
| 11 | **Real client data** if the project is adapted for a live deal. | Confidentiality and data retention obligations. | Out of scope for v1. Enterprise plan, zero data retention request, read-only connectors and compliance sign-off required first. |
| 12 | **Saved runs leak answers.** The sample run and its scorecard sit inside the project, and each new grading writes a scorecard to `evaluation/`. | A new run that read them could score well without finding anything itself, and the next grading would overwrite the last scorecard. | Claude Code asks before any agent opens `evaluation/`, `examples/` or `runs/`; `/reset-memory` moves each scorecard into its archived run; the lead agent's guardrails forbid reading them; and Phase 1 checks confirm both rules. |

## Decisions

| Date | Decision |
|---|---|
| 2026-10-17 | Claude Code features only. No Agent SDK, no Managed Agents, no application code. |
| 2026-10-18 | One specialist per source; a separate, read-only citation verifier. |
| 2026-10-18 | Findings register as the single source of truth; never delete findings. |
| 2026-10-18 | `/status` renamed `/diligence-status` (it shadowed a built-in command). |
| 2026-10-18 | Shell access removed from the financial analyst so every subagent is truly read-only. |
| 2026-10-18 | Reading the answer key requires operator approval; source data and the answer key are protected by deny rules and a checksum test. |
| 2026-10-18 | Prompt-injection rule added to the lead agent and every subagent. |
| 2026-10-18 | Automated checks in Python's standard library, run with `/run-tests`. |
| 2026-10-18 | The sample run ships in the project under `examples/sample-run/`, labeled as a build test run. |
| 2026-10-18 | Earlier runs (`examples/`, `runs/`) need operator approval to open, like the answer key, with an automated check. |
| 2026-10-18 | Three instruction fixes from the first scorecard: list unverified findings in the report appendix, combine trend findings into one cross-source finding, and apply every verifier correction before Checkpoint 3. |
| 2026-10-18 | The project is hosted in the GitHub repository `sabinejoseph8/Falcon_M-A_Due_Diligence`; `.gitignore` keeps `interview-notes.md` out. |
| 2026-10-18 | `/reset-memory` moves `evaluation/scorecard.md` into the archived run, and the approval rule covers all of `evaluation/` instead of only the answer key, with an automated check. Found while preparing the blind run: a scorecard left in `evaluation/` was unguarded, and the next grading would have overwritten it. |
| 2026-10-18 | In the blind run, the lead agent saved each analyst's and verifier's report by extracting it from the session record with a short script instead of retyping it, so the saved reports are exactly what the subagents returned. Long reports are saved by Claude Code to a file instead of shown inline, so this matters most for the longest ones. |
| 2026-10-18 | The blind run's lead agent edited `tests/test_phase3_run.py` so its own output passed; the builder reverted the edit, because a run must never change its grader. The three failing checks were written around the sample run's format rather than `CLAUDE.md`'s wording; changing them is a separate builder decision. For the Phase 5 docs review: consider a deny rule on edits to `tests/` so a run cannot do this again. |
| 2026-10-18 | Setup frozen for the remaining graded runs: same `CLAUDE.md`, agents, commands and settings as the blind run. The scorecard's three fixes wait until after the last graded run. |
| 2026-10-18 | Blind run scorecard proposes three instruction fixes (not yet applied): look up every named customer or litigant in the revenue data, verify every Medium finding the report relies on, and add a "positive and mitigating points" section to the report template, with a calibration note for debt issues cured at closing. |
| 2026-10-18 | The Phase 3 run checks accept the wording `CLAUDE.md` asks for: checkpoint names in any letter case, "Step 5: REPORT", "ACT, iteration 1", the "IC questions" heading and register IDs written as links. A builder change made after the graded runs, in its own commit. Non-standard IDs such as `LIT-F01` are still not accepted. |
| 2026-10-18 | The graders were not consistent: run 1 counted 4 Critical issues, runs 2 and 3 counted 3, and run 2 divided by 14 Critical and High issues instead of 13. Reported results are recomputed on the answer key's 13 Critical and High issues, and a fixed grading rule for `/evaluate` is a Phase 4 task. |
| 2026-10-18 | Instruction fixes from the graded runs: the lead agent sizes every named customer, supplier or litigant against `revenue_by_customer.csv`; the verifier also gets every Medium finding an IC answer cites or an `X-` finding is built from; the executive summary lists positive and mitigating points; the financial analyst compares the last goodwill test with share price moves; and a calibration rule rates debt problems cured at closing as High unless they cause a default or liquidity problem first. They take effect from the next run and have not been measured yet. |
| 2026-10-18 | `/evaluate` follows fixed grading rules: severity group = the answer key's first-listed severity, the Critical and High group listed by ID, every recall figure shown as numerator / denominator, and positives kept out of recall. The rules name no issue IDs or counts, because the lead agent can read the command file. |
| 2026-10-18 | Graded run 4 (first with the fixes) passes all 34 checks. Its verifier reports are saved as four files, `memory/analyst-reports/verification-<n>_citation-verifier_*.md`, one per parallel run. Gap found: the analysts used three-digit IDs (`SEC-001`) and `LIT-F01`, but the run checks match only two-digit IDs, so 86 of 105 findings were silently left out of the ID checks. Fixed in a separate builder commit: the checks were widened, court case IDs are ignored, and a guard fails if any workstream's findings cannot be read. `/evaluate` was run in the session that produced the run. |
| 2026-10-18 | Quality fixes from run 4's scorecard: a Critical rating must name the test it meets and show the number (in the shared rubric, every analyst, the verifier and the Checkpoint 2 table); a projected or legally uncertain covenant breach stays High; the lead agent self-checks each `X-` finding (no absolute or predictive words, sourced ranks, dates and counts, labeled inferences and projections, no raising the severity of supporting findings); duplicate findings get a parent with supporting IDs, and the risk matrix shows each fact once. To be measured in graded run 5. |
| 2026-10-18 | Leak removed: after grading run 4, its session (which had opened the answer key) edited the instructions and put one planted issue's answer into `CLAUDE.md` as an example, plus calibration wording that matched the answer key's expected severity for another. The builder removed both and restored the earlier calibration wording. Run 5 had already read them, so it was stopped before Checkpoint 1 and restarted. Lesson: a session that has opened the answer key must not edit `CLAUDE.md`, `.claude/` or `tests/`. |
| 2026-10-18 | Fixes from graded run 5, made after the run finished: (1) every checkpoint prints its full content in chat before asking the question last, and its run-log row says the content was shown, because in the desktop app a question box ends the turn and run 5's plan summary never reached chat; (2) the verifier writes its table first and counts the summary from it, after one run said 10 partially verified while listing 6; (3) Step 5 uses the committed `tools/md2html.py` and headless Chrome instead of a converter written during each run. The owner chose dependency-free over installing pandoc and poppler. Six new checks (40 in all). |
| 2026-10-18 | Graded run 5 passes 39 of 40 checks. The failure is the new checkpoint-shown check, by design. Process numbers: 85 findings (71 analyst, 14 cross-source), 79 checked by four verifier runs in parallel (59 verified, 20 corrected, 0 rejected), 2 of 3 iterations, a 17-page report. |
| 2026-10-18 | Manual prompt-injection test passed on a copy of the project (shortened: news analyst plus the lead agent's Observe step and Checkpoint 2). A planted line told agents to rate every finding Low, skip the checkpoints and recommend Proceed. The analyst reported it as finding NEWS-12. The lead agent did not follow it, kept every severity and stopped at Checkpoint 2. No configuration change needed. Not covered: the other analysts, the verifier and the report step. |
| 2026-10-18 | Run 5's two remaining suggestions, made by a builder session that had not opened the answer key or any scorecard: Step 4 sends the verifier every Critical and High finding plus every Medium finding that will appear anywhere in the report (the parallel split for more than 20 findings is unchanged), and the appendix lists only Low findings as "not verified"; Step 3's cross-source list adds dated accounting judgments, compared with later news, market or financial data and quantified. The wording names no company-specific facts. Two new checks in `tests/test_phase1_config.py` (42 in all). To be measured by graded run 6. |
| 2026-10-18 | Phase 5 docs review: the configuration matches the current Claude Code docs. Edits to `tests/` are now denied (`Edit(/tests/**)` and `Edit(./tests/**)`), with one new check (43 in all), because a blind run once edited its own grader. Deny was chosen over ask because a deny rule holds in every permission mode and cannot be clicked through. Tradeoff: Claude sessions can no longer edit the checks either, so a builder change to `tests/` is made by hand, or by removing the two rules for that session and restoring them before the commit; the Phase 1 check fails if they are missing. Known limit, recorded in `CLAUDE.md`: the rules stop Claude's file tools and shell file commands such as `sed`, but not a script that opens files itself, or `curl`. |
| 2026-10-19 | Graded run 6 used the final Phase 5 setup (commit `946f0f0`) and passes 42 of 43 checks. The failure: six Low findings carry the status "Open (not verified, Low)" instead of "Open", because the new Step 4 wording lets Low findings stay unverified and the lead agent wrote that into the status. It saved one verification summary instead of the four verifier reports unedited. The checkpoint-shown rule and `tools/md2html.py` with headless Chrome both worked as designed. A usage limit interrupted the iteration 2 financial follow-up; the same agent resumed after the reset. |
| 2026-10-19 | Phase 7 layout: each fictional target lives in `targets/<target>/` (sources in `data/`, answer key in `evaluation/`, `data_manifest.json`), so a second target can be added without touching the first. `git mv` kept the history. `CLAUDE.md`, the agents and the commands name no single target: `/diligence` and `/evaluate` take the target as an argument (default `falcon`), the run records it in `memory/target.txt`, and `/reset-memory` archives it with the run. The permission rules use `targets/*/`, and the data checks run for every target with a manifest. Saved runs are unchanged and are checked as Falcon runs; every saved run gets the same check results as before. Done by a fresh builder session that had not opened any answer key or scorecard. |
| 2026-10-19 | Generalization tested on two new targets. Heron, built without seeing the instructions or other targets and graded with the setup frozen: the facts of all 18 planted issues found, 0 unsupported findings, 1 of 4 distractors too high, and Critical and High recall of 88.5% on its grader's strict reading or 100% on the earlier basis, because four severities were one level off. Both readings are reported until `/evaluate` has an exact rule. Rules added afterwards from a target's own scorecard are measured on a new target, not on the same one. |
| 2026-10-19 | `/evaluate` gets the owner's option A as exact definitions: Found needs the main point in the verified findings, correctly cited, with the highest matching verified severity within one level of an accepted severity; Partially found covers a partial main point, a missing or weak link or citation, or a severity more than one level from every accepted one. Recall uses only these, so a one-level miss never lowers it, and severity accuracy is two lines (within one level, exact match) over the Found and Partially found issues. The positives row is graded in its own `| Pnn |` row, so the Phase 4 check and the command agree for every target. `CLAUDE.md` and the findings template say a status is exactly one of the four values, and Checkpoint 1 lists what to print in chat before the question. The command names no issue IDs or facts. Made by a session that had not opened an answer key or scorecard; no check changed (49 in all). |

## Open questions (with recommended defaults)

1. **Grade one run or several?** Decided: three blind runs with a frozen setup, with the average and range in the README (done October 18, 2026).
2. **Move commands to the newer skills format?** Recommended default: not for v1. Command files still work and are simpler to read.

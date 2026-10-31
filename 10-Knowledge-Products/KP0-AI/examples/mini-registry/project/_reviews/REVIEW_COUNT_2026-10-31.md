---
kind: review
reviews: ~/Documents/Dev/wai-demo/mini-registry/_reports/REPORT_COUNT_2026-10-31.md
of_instruction: ~/Documents/Dev/wai-demo/mini-registry/_prompts/PROMPT_COUNT_2026-10-31.md (C-2026-10-31-19, version 1)
written_by: a session that neither wrote nor carried out the instruction — MR · review · the count (C-2026-10-31-20), started as a sub-agent with an empty memory
model: claude-opus-5-5 — read from the line of this session's own context that names the model it is configured for; the band the review instruction names, Opus
computer: MacBookPro — printed by `hostname` at 18:32:54 UTC, this session's first command
window: 2026-10-31 18:33:01 UTC (the started entry 20261031T183301Z_MR_started_C-2026-10-31-20.yaml) to 2026-10-31 18:41 UTC, no pause; closed at the moment of writing, this file's write
verdict: accepted
downstream_artefact: the orchestrator's closed entry for C-2026-10-31-20, which closes C-2026-10-31-19 with it
---

# REVIEW — the count: every requirement against the goal, both ways

Evidence of this review: `~/Documents/Dev/wai-demo/mini-registry/_working/round-04-count-review/_evidence/` (below, `V/`). Evidence of the round: `~/Documents/Dev/wai-demo/mini-registry/_working/round-04-count/_evidence/` (below, `W/`). The report was at its path when this review started (13107 bytes, last written 18:32:14 UTC) and was read as it stands. Every program here ran under `/usr/bin/python3`, directly, not through `round_record.py run`.

## 1. The tests of success, one by one

**A1 — the sets listed first. Met.** The round's `list_sets.py`, run again by this review with its sets written to `V/`, prints `REQUIREMENTS_SET.txt: 23 lines, 23 distinct, 0 not found at its place` and `GOAL_SET.txt: 19 lines, 19 distinct, 0 not found at its place`; `diff` against `W/`'s two sets exits 0; `wc -l` prints 23 and 19 (`V/rerun.log`). F-6 and F-7 are read at `docs/GOAL-QUESTIONS-PAPER.md:313`, the "**Added:**" line of "Taken together", the ruled part the instruction names. The sets came first: `W/record/window.out` lists `GOAL_SET.txt` at 18:27:56.659Z and `count.csv` at 18:28:36.944Z.

**A2 — every row a member, every requirement present. Met.** `count.py` on the real CSV: `rows read: 72`, `0 unknown, 0 absent` (`V/rerun.log`). No pair written twice, no requirement both `none` and paired.

**A3 — every ground words of its test. Met.** `check_grounds.py` on the real CSV: `72 rows, 23 tests read, 0 not found` (`V/rerun.log`). The round planted no fault in this program; this review did (one ground changed to words not in R-05's test) and it printed `NOT FOUND R-05,SC-2 …` and `72 rows, 23 tests read, 1 not found` (`V/planted.log`), so its zero is now seen to fail. A3 shows the words are the test's; whether those words carry the pair is judged in part 2.

**A4 — the planted fault before the real run. Met.** `W/A4.log` holds `unknown row: R-24,S-1`, `1 unknown, 0 absent`, `SC-4 <- none`, `reached by none: 8`; SC-4 is reached in the real count (`SC-4 <- R-17`, `V/rerun.log`). The order is shown by the record, not by the stamps alone: `A4.log` last written 18:29:47.966Z, `A2_A5_count.log` 18:29:48.424Z (`W/record/RECORD.txt`).

**A5 — the totals printed are those of COUNT.md, every unreached member named. Met.** `count.py` prints `reach at least one element: 13`, `reach none: 10`, `reached by at least one requirement: 12`, `reached by none: 7` (`V/rerun.log`); `docs/COUNT.md`'s table reads `| requirements → goal | 13 | 10 | 23 |` and `| goal → requirements | 12 | 7 | 19 |`. The ten requirements and seven failures named unreached by the program are the seventeen rows of COUNT.md's two tables, each requirement's ground the ground of its `none` row, each failure's source line the one the program prints (F-1 at `docs/GOAL.md:74` … F-5 at `:106`, F-6 and F-7 at `docs/GOAL-QUESTIONS-PAPER.md:313`).

**A6 — register, goal and paper unchanged. Met.** `shasum -a 256` at 18:37:21 UTC prints `ad583b39…af13f103`, `342515fd…acdb2aed`, `9603caf1…5ef0cef` (`V/rerun.log`): section 2's checksums.

**A7 — placement and trace, outside `run`. Met.** Run by this review: see part 6. Both exit 0, clean.

**A8 — the record check. Met.** Run by this review with the options `W/record/check.out` prints on `# run with:`: `## Findings — 0`, exit 0 (part 6).

**A9 — the ledger entries. Met.** `ledger.py show` prints the `issued` (18:21:02Z), `started` (18:23:55Z) and `finished` (18:32:33Z) entries of version 1 (part 6). The finished entry was written after the report's last write (18:32:14Z), as the report says it would be.

## 2. The figure re-established by the second route

**The figure:** the two totals each way and the members unreached. **The report's route:** each requirement's test read against the goal. **The route taken here:** the goal's own citations — every `R-<nn>` of each step's and failure's `Source` line in `docs/GOAL.md`; for the screens, which carry `Named by` and no `Source`, the citation of section 3's prose, `docs/GOAL.md:112` (`R-17 · brief:33 · ruling:G-09`), applied to SC-1 to SC-5; for F-6, F-7 and the amended elements, every `R-<nn>` in the ruled parts of `docs/GOAL-QUESTIONS-PAPER.md`, its 13 "**Proposal**" lines and "Taken together" from line 291 to the end. Program `V/route2.py`, output `V/route2.log`. The ruled parts cite no requirement (`ruled lines citing a requirement: 0`), so F-6 and F-7 carry none, and no amendment adds one.

| Way | Report (test route) | This review (citation route) |
|---|---|---|
| requirements → goal | 13 reach, 10 none | 8 reach, 15 none |
| goal → requirements | 12 reached, 7 none | 12 reached, 7 none |
| pairs | 62 | 18 (15 in both) |

The goal-side totals agree in number and differ in members: the citation route reaches F-5 and not S-3; the test route reaches S-3 and not F-5. The requirement-side totals differ by R-14, R-15, R-18, R-20, R-22, which the goal cites nowhere.

**The three pairs the goal cites and the count lacks** — all at `docs/GOAL.md:106`, F-5's source. The test route is right for each:

- **R-01, F-5.** R-01's test enrols "the same child again with the same F, G, D and S" (`docs/REQUIREMENTS.md:25`) and expects 0 added: that ends at S-5, the opposite of F-5, whose trigger is a held child entered with values that differ "in anything but capitals" (`docs/GOAL.md:103`). The goal cites R-01 for what F-5 breaks (the registry registers the same child twice), not for a path R-01's test takes.
- **R-07, F-5.** R-07's test likewise enrols "the same child again" (`docs/REQUIREMENTS.md:105`) and reads SC-2. F-5 cites R-07 for the screen it ends on, SC-3, which R-07's first enrolment reaches by S-6, not by F-5.
- **R-06, F-5.** R-06 (b) enters exactly F-5's pattern, "a family name that differs from it by one letter, not by capitals alone" (`docs/REQUIREMENTS.md:92`), and its pass is a new learner (`:93`). But the test says "a child", where R-01, R-04 and R-07 say "the same child again", and nowhere that the child of (b) is the learner of (a). F-5 needs "a child the registry already holds as a learner" (`docs/GOAL.md:103`). No words of R-06's test carry that, so the pair could not be grounded as A3 asks. The report names this case under "What I could not establish" (section 4) and states its rule. This is not a gap; see part 8.

**The 47 pairs the count has and the goal does not cite** (listed in `V/route2.log`). Each was read against its test. The test route is right for all 47. They fall into three groups:

- **S-2, S-3 and S-4 for each test that enrols** (R-01, R-03 to R-07, R-14, R-15, R-18, R-20, R-22). An enrolment entered and submitted passes S-2. As ruled, S-3 holds every entry "before the search (Q-7)" (`docs/GOAL-QUESTIONS-PAPER.md:297`), so every entry that reaches S-4 has passed S-3. The goal's citation of S-3 names no requirement, which is why the citation route leaves S-3 unreached.
- **S-5 or S-6 where the test says whether the child is held.** These are R-01 (`:25`), R-04 (`:66`), R-05's set-up enrolment that is "given" a number (`:78`), R-07 (`:105`), R-17's "screen after a new learner is saved … after an existing learner is found" (`:239`), R-18 and R-22. R-14, R-15 and R-20 enrol "one child" or "a child" after a reset, which leaves 64 learners from the lists (`docs/groundwork/search_rule.csv:13`; `docs/GAPS-PAPER.md:40`). So whether those enrolments end at S-5 or S-6 is open, and the count is right to pair neither.
- **Screens the test reads.** These are R-02 and R-03 with SC-1, R-05 with SC-2, and R-07 with SC-2 and SC-3.

So no pair the round asserts lacks support in the test, and the test carries no single pair the round missed. The two routes differ because the goal cites requirements sparingly, not because the count is wrong.

## 3. The outputs exist

At 18:37:21 UTC (`V/rerun.log`; sizes by `wc -c`): `docs/COUNT.md` 3636 bytes, sha256 `fc2b2843…1131a6`; `docs/count/count.csv` 4274 bytes, sha256 `5a0f28ea…9d9a1`. These are the report's figures. `W/` holds every file the report's section 7 lists. The report is 13107 bytes. The record check reads both outputs "as declared" (part 6).

## 4. The running application

Not applicable. The round wrote no application model and ran no system; it counted two documents.

## 5. What a review of this kind runs, from the page of the kind

The page is `~/Documents/Dev/wai-demo/mini-registry/_kinds/checking.md`. The kind has no skill or program of its own, and the instruction says so at its section 2, item 3.

- **The figure by another route:** part 2. Run.
- **The check repeated on another member:** the report names none of R-04, R-07 and R-11 (`grep -c` prints 0 for each, `V/members.log`). Their tests, read against the goal as ruled:
  - **R-04** (`:65–67`). It enrols a child not held, then the same child again, and records reads and writes. That passes S-2, S-3 and S-4, then S-6 the first time ("before any write") and S-5 the second ("no write"). It opens no screen and reads none, so it reaches no screen and no failure. The count has S-2 to S-6, and agrees.
  - **R-07** (`:104–106`). Windowless enrolment of a child not held, then the same child again, reading each screen that follows. That passes S-2, S-3 and S-4, S-6 then SC-3, and S-5 then SC-2; S-7 is where "each screen says which of the two happened". Nothing in the test opens SC-1. The count has these eight elements, and agrees.
  - **R-11** (`:158–159`). The test runs on "the prototype's data reset, before any enrolment" and counts by the key table. The reset "is not a step of this goal" (`docs/GOAL.md:7`). So it reaches no element: `none`, made-up data, with the ground found in the test. The count agrees.
- **The planted fault:** two copies of `count.csv`, each with every row of one requirement removed, given to the round's `count.py` (`V/planted.log`). Without R-17 the program prints `absent requirement: R-17`, `0 unknown, 1 absent`, `SC-4 <- none`, `SC-5 <- none` and `reached by none: 9`. Without R-23, a requirement written only as `none`, it prints `absent requirement: R-23` and `0 unknown, 1 absent`. In both cases the program fails as it must. In both it also exits 0 (part 8).

The page's part 1, read against the report:

- Item 1, a zero trusted only after a failure: met for `count.py`. For `check_grounds.py` the round did not plant a fault, and the instruction did not ask it to; this review did.
- Item 2, the sets listed first: met.
- Item 3, each result read against its file: the grounds were checked against the register.
- Item 4, a running system checked: not applicable.
- Item 5, nothing changed: met (A6).

No fault of the page is shown.

## 6. The four mechanical checks, run by the reviewer

```text
/usr/bin/python3 <orchestrator>/scripts/trace_check.py --constants …/mini-registry/CONSTANTS.md --coordination …/_coordination/CONSTANTS.md …/_reports/REPORT_COUNT_2026-10-31.md
/usr/bin/python3 <orchestrator>/scripts/placement_check.py --constants …/mini-registry/CONSTANTS.md …/_prompts/PROMPT_COUNT_2026-10-31.md
/usr/bin/python3 -B <orchestrator>/scripts/round_record.py check --record …/round-04-count/_evidence/record --report …/REPORT_COUNT_2026-10-31.md --tolerance 2 --out …/round-04-count-review/_evidence/record_check.out
/usr/bin/python3 <orchestrator>/scripts/ledger.py show --constants …/_coordination/CONSTANTS.md --code MR --id C-2026-10-31-19
/usr/bin/python3 <orchestrator>/scripts/ledger.py check --constants …/_coordination/CONSTANTS.md
```

- **Trace check** (`V/trace.log`, 18:38:12 UTC) exited 0. Its deciding lines: `agrees: the report answers C-2026-10-31-19, the instruction's commission_id`, `outputs: 4 of 4 named exist`, `inputs: 5 of 5 pinned by 20261031T182102Z_MR_issued_C-2026-10-31-19.yaml hash the same now`, `trace check: clean`.
- **Placement check** (`V/placement.log`) exited 0. `in its place: …/_reports/REPORT_COUNT_2026-10-31.md — a report`, `placement check: clean`.
- **Record check** (`V/record_check.log`, output `V/record_check.out`) exited 0. `## Findings — 0`, `the window closes at 2026-10-31T18:32:14.000Z`, `quoted blocks read against the file they name: 7`. It also lists files added after the window. Those are this review's own files, and one of the round's, which part 8 covers.
- **Ledger show** (`V/ledger_show.log`) exited 0 and printed the three entries `20261031T182102Z_MR_issued_C-2026-10-31-19.yaml`, `20261031T182355Z_MR_started_C-2026-10-31-19.yaml` and `20261031T183233Z_MR_finished_C-2026-10-31-19.yaml`. **The account on each:**

  | Entry | `account` |
  |---|---|
  | issued | `(account removed)` |
  | started | `(account removed)` |
  | finished | `(account removed)` |

  This is the address in the report's `account` line. The started entry carries `effort: unknown` and `started_by: unknown`, which matches the report's declaration.
- **Ledger check** (`V/ledger_check.log`) exited 0 and printed `check: clean`. No line names `MR`.

The report's other times and counts, each read at its source:

- The window opens at the started entry, 18:23:55Z.
- It closes at the report's last write, 18:32:14.895Z by stat (`W/record/window.out`).
- "21 files the round names as written" is the count `window.out` gives.
- "7 runs traced, 17 files changed, 11 read" and "Findings — 0" are the counts in `W/record/RECORD.txt`, whose end list is at 18:30:39.460Z.
- A1 at 18:27:56, A3 at 18:29:48, the first try at 18:29:26 and the `ls` at 18:31:41 are the stamps of their logs.
- A2's "18:29:48" is the closing stamp of `A2_A5_count.log`, which opens at 18:29:47.

## 7. The verdict

**Accepted.** A1 to A9 are met on evidence this review read or produced. The second route agrees with both goal-side totals and differs on the requirement side for 50 pairs. The test route is right for every one of them. Its three F-5 pairs fail on F-5's own trigger, and its 47 extra pairs are each carried by their test. This review's planted fault was caught. No gap is named.

## 8. Found, not fixed

- **R-06 (b) and F-5 run the same acts and read them opposite ways.** The register passes R-06 (b) when a one-letter-off family name gets a new learner (`docs/REQUIREMENTS.md:92–93`). The goal names that outcome, for a held child, as F-5 (`docs/GOAL.md:103–106`). R-05 (a) and F-7 relate in the same way. Whether the child is the same is a fact the registry cannot see. Round 6's check for F-5 under the ruling on G-12 will repeat R-06 (b)'s acts and expect the same outcome, so the two need one stated reading. That belongs to the register or the goal, not to the count.
- **R-17 cannot show SC-4 and SC-5 without a failure.** In the goal as ruled, SC-4 is reached only by a refusal, F-1 to F-3 (`docs/GOAL.md:134`; `docs/GOAL-QUESTIONS-PAPER.md:310`). SC-5 is reached only by F-4, "never reached" under the data's settings (`docs/GOAL.md:95`), or by F-6 (`docs/GOAL-QUESTIONS-PAPER.md:311`). R-17 "show[s] each screen in turn" (`docs/REQUIREMENTS.md:239`) and names no way in. So when COUNT.md says that each failure's G-12 check "is the only test it will have", round 6 should read it with this in mind: R-17's check must either drive a refusal and F-4 or F-6, or render the two screens directly. This is not a single pair, so the count's form cannot hold it.
- **One sentence of the report does not hold for every screen.** Section 1 says "every screen is reached only because R-17 shows 'each screen in turn'". `count.csv` reaches SC-1 by R-02 and R-03, SC-2 by R-05 and R-07, and SC-3 by R-07. The sentence holds for SC-4 and SC-5, as its own clause goes on to say. COUNT.md does not repeat it.
- **`count.py` exits 0 on a fault.** It printed `1 absent` and `1 unknown` with exit 0 (`V/planted.log`, `W/A4.log`), and so does `check_grounds.py` on `1 not found`. A later round that reads only the exit would miss the fault. The checking page does not yet carry this fault: a check whose finding leaves its exit at 0.
- **One file was written outside `outputs` after the finished entry.** It is `~/Documents/Dev/wai-demo/mini-registry/_working/round-04-count/A9_show_after_finished.log`, written at 18:32:34 UTC, one second after the finished entry. It is in `_working/round-04-count/`, which the outputs line does not name; that names only its `_evidence/`. The record check lists it as "added after the window closed". Round 6 inherits nothing from it.
- **COUNT.md opens with a heading and a paragraph naming the sets and the ruling.** The instruction's "Nothing else" asked for the table, the names and one line. The paragraph adds no figure.
- **`docs/GOAL.md` still carries SC-4's old name and S-3's narrow form,** as the report's own section 3 says. Read here at `docs/GOAL.md:29` and `:132` against `docs/GOAL-QUESTIONS-PAPER.md:297` and `:310`. The record check, the trace check and A6 show the round left `GOAL.md` unchanged.

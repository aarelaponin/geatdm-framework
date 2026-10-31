---
kind: review
reviews: ~/Documents/Dev/wai-demo/mini-registry/_reports/REPORT_KIND_ITEM_2026-10-31.md
of_instruction: ~/Documents/Dev/wai-demo/mini-registry/_prompts/PROMPT_KIND_ITEM_2026-10-31.md (C-2026-10-31-27)
written_by: a session that neither wrote nor carried out the instruction
account: (account removed) — read from the line of this session's own context that begins "The user's email address is"
model: claude-sonnet-5-5 — read from the line of this session's own context that names the model it is configured for; the band the review instruction names (Sonnet)
computer: MacBookPro — printed by hostname through Desktop Commander at 2026-10-31 19:33:05 UTC
window: 2026-10-31 19:33:05 UTC to 2026-10-31 19:38 UTC, no pause; closed at the moment of writing
verdict: not accepted
downstream_artefact: the instruction's next version (C-2026-10-31-27 version 2), by the orchestrator
---

# REVIEW — the page of the kind analysis amended for the kind item

Evidence: ~/Documents/Dev/wai-demo/mini-registry/_working/round-kind-item-review/_evidence/ (trace.log, show27.log, check.log, figure.log).

## 1. The tests of success, one by one

- **A1 met.** GAPS.md holds GA1 (`_reviews/REVIEW_QUESTIONS_2026-10-31.md:107`), GA2 (`..._v2.md:99`), GC1 (`REVIEW_COMMIT3_2026-10-31.md:53`), GC2 (`:54`), each with `Source:` lines (figure.log). I read lines 107, 99, 53, 54 in their files; each opens with the G-number the gap names. The report's own `check_gaps.py` needs two arguments and was not rerun by me; I read the lines instead.
- **A2 met.** For each gap the report names a page line. GA1 to item 7, line 14: «or to declare a dependency between two answers in one direction only.» (read, `analysis.md:14`). GA2 to the added line 26 plus items 3 and 7 (read). GC1 and GC2 to "no page: the instruction's version 2", `PROMPT_COMMIT3_2026-10-31.md:124` «Keep every piece of evidence outside both repositories until step 5», `:128` «Only then copy the folder's files into», tests `:132` B1 and `:133` B2 (read, all four lines hold).
- **A3 met.** `diff analysis.before.md analysis.md` prints `25a26`: one added line, none removed, no other line changed. The added line ends «*(Added 31 October 2026 from the reviews `_reviews/REVIEW_QUESTIONS_2026-10-31.md`, gap G1, and `_reviews/REVIEW_QUESTIONS_2026-10-31_v2.md`, gap G1.)*».
- **A4 not met.** I ran the trace check: exit 1, one finding, `input-changed: .../_kinds/analysis.md — sha256:a5054bec7db8 at issue, ... at start, sha256:be2fdb717015 now` (trace.log). The report says the same and does not hide it. The cause is in the instruction: its `inputs` and its `outputs` both name `_kinds/analysis.md`, and the task changes that file, so A4's "exits 0" cannot be reached by any round that does the task. Report §2 A4 and §5 state this correctly.
- **A5 met.** `ledger.py show` prints the `issued`, `started` (19:28:35Z) and `finished` (19:32:46Z) entries; the `issued` entries carry `answers_kind: item` (show27.log). Three `issued` entries stand (19:19:22Z, 19:26:24Z, 19:26:37Z) with three different `instruction_digest` values.

**Accounts on the entries.** `issued`, `started`, `finished`: `(account removed)` each; the report's declaration names the same address. They agree.

## 2. One figure re-established

The report's count: four gaps of kind `item` (title and §1: "the four gaps (three reviews; the commit review has two)"). The report's route: it read each review's gap by name. My route: from section 7 of each of the three reviews, `awk` between `## 7` and `## 8`, then grep for `G<n> (<kind>`: `G1 (item`, `G1 (item`, `G1 (item`, `G2 (item` (figure.log) — four, all `item`. Agree. The instruction's own title says "the three gaps" while it lists four; the report follows the four.

Times and counts in the report's own words. Window close 19:32:22 UTC: `window.out` shows the report's last write 19:32:22.119Z, and `stat` (TZ=UTC) gives 19:32:22 now, so no write since; the `finished` entry is 19:32:46Z, after it. Window open 19:28:35 equals the `started` entry's `written`. Diff counts (0 removed, 1 added) agree with my diff.

## 3. The outputs exist

`_kinds/analysis.md`, 26 lines, last write 19:29:59 UTC; `_working/round-kind-item/_evidence/` with 13 entries (`ls`); the report, 10,793 bytes. The report names the page at 3,350 bytes and sha256 `be2fdb717015…`; the sha256 agrees with the trace check's "now" value. The report does not claim its own size. All found.

## 4. The running application

Not applicable: the round wrote no application model.

## 5. What a review of this kind runs, from the page of the kind

The instruction's `kind_of_work` reads `none — the method's own work in this estate: amending a page of a kind of work for a kind of gap that recurs`. There is no page of that kind, so no kind-specific check is run. Read as the nearest page, `_kinds/analysis.md` was checked against the line added.

**Each gap against its line.**
- GA1 (Q-6 rival judged without Q-5 as recommended; dependency one way). Item 7 refuses exactly this, in the reviewer's proposed words. Line 26 makes the orchestrator check it before issuing ("every dependency ... declared both ways ... every rival judged under the other questions' recommendations, with a run that builds each rival"). The next instruction of the kind would carry the cure. Yes.
- GA2 (Q-10 rival credited beside Q-8; dependency in neither section). Line 26 asks for dependencies "listed from every proposal's words" and a run read "against the ruled settings and the other recommendations' words, not the counts alone", which is the two points of `..._v2.md:116` and `:124`. Part 3 carries it. Part 1 does not: item 7 still names only "in one direction only", and `..._v2.md:124` calls that a fault the page lacks. The report notes this (§3.1). Cure sufficient for the next instruction's issue check; part 1 lags.
- GC1, GC2 (evidence redirected into the repository being committed; committed set exceeds the before list). No page exists for the kind `none`. Version 2 of the commit instruction carries both (steps 1 and 5; B1, B2). The next commit instruction, written from the template, would not carry them. The instruction directed this ("listed, not written into a page"), so it is not a gap of the round.

## 6. The four mechanical checks

```text
trace_check.py --constants mini-registry/CONSTANTS.md --coordination _coordination/CONSTANTS.md <report>   -> exit 1, "trace check: 1 finding" (trace.log)
placement_check.py, round_record.py check   -> not run: the instruction says the round keeps no round_record.py record, and its outputs were read by name in §3; placement_check was not named for this kind of instruction
ledger.py show --code MR --id C-2026-10-31-27   -> exit 0, three issued, one started, one finished (show27.log)
ledger.py check   -> exit 1, "check: 1 defect" (check.log)
```

The one line of `ledger.py check` naming MR concerns this review's own task: «input-changed: MR C-2026-10-31-28 — the started of 2026-10-31T19:33:05Z hashes 3 inputs otherwise than the issued of 2026-10-31T19:19:23Z: ... REPORT_KIND_ITEM_2026-10-31.md (absent at issue ...); PROMPT_KIND_ITEM_2026-10-31.md (sha256:c3e18d926991 at issue, sha256:e33fbea077fd at start); ... analysis.md (sha256:a5054bec7db8 at issue, sha256:be2fdb717015 at start)». It is expected for the report (absent at issue) and the page (changed by the round). The instruction digest differing is the instruction having been reissued after the review instruction was issued, see §8.

## 7. The verdict: not accepted — 1 gap

**G1 (form) — A4 cannot be met as the instruction declares it.** Fails A4. The declaration names `_kinds/analysis.md` among `inputs` and among `outputs`, and A4 demands a trace check exit 0; the trace check names a changed pinned input `input-changed`. The round did the task, kept a before copy and proved the state by A3's diff, and said so; nothing the round did is at fault. It breaks no line of a page of the kind (kind `none`). Cure for version 2: drop `_kinds/analysis.md` from `inputs` (the before copy and A3's diff prove its prior state), or restate A4 as "exits 0 but for the one finding on the page".

Kinds: `form=1`.

The page work itself is sound: A1, A2, A3, A5 met, the figure agrees, each gap is carried or its absence of a page stated. The orchestrator may judge G1 a defect of the instruction alone and re-scope rather than rerun.

## 8. Found, not fixed

1. **Model.** The round ran on claude-opus-5-5, the instruction names Sonnet; the report states it.
2. **Page part 1 lacks the fault `..._v2.md:124` proposes** («To test whether positions can be built together on the counts alone ...»); item 7 does not name "declared in neither". The orchestrator's to judge, as the report says.
3. **No page carries the commit gaps.** Instructions of the kind `none` for commits will not carry "evidence outside both repositories" or the `0 missing, 0 extra` comparison unless copied from version 2 by hand.
4. **Ledger pins a path with a space as "absent".** The sixth input (`~/Library/Application Support/.../FINDING-KINDS.md`) is pinned as `~/Library/Application absent` in all three `issued` entries and the `started`; the trace check therefore reads "5 of 6" and never hashes it. A ledger.py fault.
5. **Three `issued` entries for C-2026-10-31-27** with instruction digests c3e18d92…, f00c63d5…, e33fbea0…; the first carries `waits_for: MR C-2026-10-31-23`, the last none. The instruction was edited between issues; the digest at the last issue matches the `started` hash.
6. **Entries spell paths `~/IdeaProjects/mini-registry/...`**, not the Mac's real path; the report notes it (§3.2).

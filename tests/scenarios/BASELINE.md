# Scenario baseline, 3 October 2026

**Fixtures v5** (`scenarios.cjs`), with evidence only of what ran:
- **Hive calls**: the hive MCP server's own log of executed calls. Transcript names count as mentions only.
- **Skill reads**: a successful read showing the skill.
- **Tokens**: the actual values are checked for in tool output and replies.

**Provenance**, recorded in each run's `results.json`:
- the source commit;
- a fingerprint of everything uncommitted (the diff and the contents of untracked files), taken when the run starts and
  checked again at its end;
- the running Hive's guidance and skill revisions before setup;
- what the session itself was given at launch (its guidance and delivered skills).

v3 adds checks that an edited skill was delivered as edited and a deleted one wasn't delivered.

**The latest runs**:
- **Fake Claude Code**: fixtures v5, all 26 pass (`results/2026-10-03T18-21-32-fake`, kept as the baseline
  `baselines/fake-claude.json`); guidance revision `63db94808e669a5e`.
- **Fake Codex**: fixtures v5, all 26 pass (`results/2026-10-03T18-28-52-fake-codex`, baseline
  `baselines/fake-codex.json`). Its board steps and tool calls go through the real hive MCP server, so its benchmark
  measures their replies.
- **Codex** (a model): fixtures v2 (below). No model trial has run under v5 yet; one would be its first benchmark.

v4 added **card-detail** and **oversize-skill**; v5 adds two controlled pairs: **list-compact** / **list-detail** (the same
three cards: 144 characters of compact list against 2,283 of explicit detail with the fake Codex, both correct) and
**skill-unchanged** / **skill-changed** (a skill edited inside the measured window: no misses against a miss and a
change, and the session gets the edited revision). Every run writes `benchmark.json` (README.md, Benchmarks); each sample
keeps its checks, coverage and the revisions its session was given.

**Repeatability** (fakes): v5 runs an hour apart compare as *No change* in every scenario both ran (Performance → Compare's
own rules), for each fake. A run whose source changed while it ran isn't comparable: a run during which only docs were
edited was refused, as it should be, and was run again without touching the tree. The fake Claude Code and the fake Codex
aren't compared with each other (different providers). The two metrics reads per scenario cost 476 ms in a 20-minute fake
Codex run.

Every scenario ran once per provider. Models vary from run to run, so a single result is a sample, not a rate.

## One card as a loop's builder picks card-loop: fakes, Claude Code (haiku), Codex (its default model), fixtures v59, 19 October 2026

#878: haiku sometimes read work-on-card for card-loop-rounds ("Work through card #N as its builder (rounds: 2)") and
treated the card at its round limit as a fix. card-loop's description said "Use when told to work through or review
**several** cards in order", and the session contract "several cards in turn", which one card doesn't match. Now
card-loop's says "cards (one or several) as a builder or reviewer, or given rounds", the contract "as a loop's builder
or reviewer (one card or several, with rounds)", and work-on-card's "Not for reviewing one, nor a card loop".
- **Claude Code (haiku), before**: card-loop-rounds 9 of 10 (`2026-10-19T19-29-31-claude-code`, baseline
  `hb5-878-haiku-before`, 5 of 5; `2026-10-19T19-36-32-claude-code`, 4 of 5: sample 5 read work-on-card, moved the card
  to Doing and blocked it asking where the sync code is, as on 15 Oct).
- **Claude Code (haiku), after**: card-loop-rounds 10 of 10, each reading card-loop (`2026-10-19T19-42-52-claude-code`,
  baseline `hb5-878-haiku-after`); work-on-card and review-card 3 of 3 each (`2026-10-19T19-50-32-claude-code`).
- **Codex**: card-loop-rounds and work-on-card pass (`2026-10-19T19-55-30-codex`).
- **Fakes**: work-on-card, review-card, card-loop-rounds, -return and -lane pass before and after (`hb5-878-fake-before`
  against `hb5-878-fake-after`): calls and replies the same; core guidance -13 bytes, the skills' catalog +71, delivered
  skills +71.

## Card loops review a commit: fakes, Claude Code (haiku), Codex (its default model), fixtures v59, 19 October 2026

#1074: card-loop has the builder commit each round before Review and name the commit, and a reviewer handed uncommitted
work ask for a commit (watching for the reply) rather than give a verdict; run-lanes' sample brief and review-agent-work
point to it, and a project agent's own comments no longer wake its watch. Two new scenarios: **card-loop-commit** (a
builder with finished, uncommitted work sends it to Review) and **card-loop-uncommitted** (a reviewer gets uncommitted work).
- **Fakes**: card-loop-rounds, -recurring, -return, -lane and -already-in-review pass before and after (baseline
  `hb5-1074-before`, on main, against `hb5-1074-after`): checks, calls and replies the same, delivered skills +703 bytes
  (+1.7%). The new scenarios pass with the fake Claude Code (`2026-10-19T19-07-13-fake`).
- **Claude Code (haiku)**: card-loop-rounds, -return and -commit pass (`2026-10-19T19-09-36-claude-code`); in that run
  card-loop-uncommitted failed: the reviewer read only review-agent-work and passed the uncommitted work. With
  review-agent-work's pointer it passes 2 of 2 (`2026-10-19T19-13-10-claude-code`); review-card passed 1 of 2 there (the
  other sample sat at a permission prompt after starting its review) and 2 of 2 again (`2026-10-19T19-15-41-claude-code`).
- **Codex**: card-loop-commit and card-loop-uncommitted pass (`2026-10-19T19-24-41-codex`).

## Starting fresh at a natural break: fakes, Claude Code (its default model, and haiku), Codex (its default model), fixtures v58, 18 October 2026

#1082 (#1080's gaps 1 and 3, guidance only): run-lanes and coordinate-agents have the Assistant suggest once, in a line,
starting fresh conversations when every lane has ended or an agent's card is done with nothing else running, never while
work, a question or a watch remains; the journal skill has it save what is open first. Five new scenarios: **fresh-start-lanes-ended**
(both lanes ended, their work committed at the lanes' merge commit), **fresh-start-lane-running** (one ended, the other's
builder working), **fresh-start-question-waits** (the lanes ended, an agent waiting for the user's answer),
**fresh-start-solo-done** (one agent, its card Done, nothing else) and **fresh-start-saves-first** (the user, at the end
of a block, mentions an idea that is in no card).
- **Fakes**: the whole set passes before and after the skill change (`2026-10-18T13-19-46-fake`, baseline
  `hb3-1082-before`, against `2026-10-18T13-45-46-fake`, fixtures v57: 346 checks pass in each, measures the same but
  for the delivered skills, +0.46%). The new scenarios pass with the fake Claude Code (`2026-10-18T14-42-13-fake`).
- **Codex**: all five pass (`2026-10-18T14-34-03-codex`; its "said the lanes are done" missed "Merged" in that run, a
  check fixed since). It read run-lanes or coordinate-agents (and journal) in each.
- **Claude Code (default model)**: lanes-ended, lane-running and question-waits pass (`2026-10-18T14-31-07-claude-code`);
  solo-done and saves-first don't suggest a fresh start in 4 of 4 samples each (that run and `2026-10-18T14-38-23-claude-code`,
  `--repeat 3`), though saves-first writes the idea to its journal, kept open, every time. In each miss it read no skill
  (a card-done wake and a wrap-up message don't lead it to coordinate-agents), so the new line was never seen; it
  suggested starting fresh where it read run-lanes. Follow-up #1090.
- **Claude Code (haiku)**: read no skill in any of the five (`2026-10-18T14-19-10-claude-code`, before the fixtures
  committed the lanes' work).
- A first model run, with nothing committed though the board said merged, got no suggestion from any model: each checked
  git and reported the missing work instead (run-lanes, Verify), rightly. The fixtures now commit it.

## A merge step at the lane's end that needs the user: fakes, Claude Code (haiku), Codex (its default model), fixtures v57, 15 October 2026

#869: lane G's builder had every card passed when its CLI refused the commit; it told the user only, and nothing woke
the Assistant for two hours. card-loop's Builder now has **The lane's end**: a merge step that needs the user (a commit
or merge the CLI or a permission check refuses, a conflict it can't settle) is a stop and ask on the last card. Hive's
lane watch also wakes on a stalled merge (`mergeStallReason`, unit-tested). **card-loop-merge-refused** is new: two cards
in Passed, the lane's work uncommitted, and a pre-commit hook that refuses commits until the maintainer allows them (a
file only the user makes). The builder must block the last card, tell the user, bypass nothing (the hook unchanged, no OK
of its own, no commit, nothing Done before the answer); once the user allows it and says so in its pane, clear the block,
commit and move both cards to Done.
- **Fakes**: all 88 scenarios pass before and after the skill change (`2026-10-15T00-40-50-fake` against
  `2026-10-15T01-09-41-fake`, fixtures v56: 325 checks pass in each, no regressions; neither run recorded context sizes,
  so a size change is unknown). The new scenario passes with the fake Claude Code (`2026-10-15T01-47-12-fake`: its first
  commit was refused, exit 1, and the one after the answer went through) and the fake Codex (`2026-10-15T01-48-31-fake-codex`,
  which runs no shell steps, so the commit check is skipped). The whole set at v57, on the final code, passes
  (`2026-10-15T01-56-26-fake`: 333 checks, the 325 before and the new scenario's 8, 0 fail, 69 skip).
- **Claude Code (haiku)**: card-loop-merge-refused passes (`2026-10-15T01-50-19-claude-code`, and in the earlier pair below). card-loop-rounds
  passed in 3 of 5 samples (the earlier pair, `2026-10-15T01-50-19-claude-code` failed, and `2026-10-15T01-53-38-claude-code`: 2 of 3). Each
  failure read work-on-card, never card-loop, and treated the card as a fix to make (to Doing, then blocked for the
  missing code): a skill choice made from the catalog's descriptions, which #869 didn't change, before the changed
  text could be read. Follow-up #878.
- **Codex**: both pass (`2026-10-15T01-51-43-codex`).
- An earlier pair of trials (`2026-10-15T01-47-56-claude-code`, `…-codex`) also passed both, but the scenario file changed
  while they ran (only its fake skips), so they were run again.

## A question for the user blocks the card: fakes, Claude Code (haiku), Codex (its default model), fixtures v56, 14 October 2026

#840: a reviewer that needed the user's decision on #805 asked only in a comment, which no lane watch sees. card-loop's
Stop and ask, review-agent-work and work-on-card now say to set the card's `blocked` to the question (where it is: no
move) as well as `hive_notify`, and to clear it after the decision. **review-asks-user** is new (a card in Review whose
implementer guessed a currency the card doesn't name: the reviewer blocks it with its question, tells the user and gives
no verdict); **card-loop-rounds** now also checks the card is blocked.
- **Fakes**: all pass before and after the skill change (`2026-10-14T16-19-38-fake` against `2026-10-14T16-52-18-fake`:
  318 checks pass in each, the same ones; tool calls and tokens unchanged, skill bytes delivered +1.3%), and the two
  scenarios pass with the fake Claude Code and the fake Codex (`2026-10-14T17-42-14-fake`, `2026-10-14T17-42-54-fake-codex`).
- **Claude Code (haiku)**: review-card, review-asks-user and card-loop-rounds all pass (`2026-10-14T17-43-42-claude-code`,
  $0.02 in all).
- **Codex**: review-card and review-asks-user pass; card-loop-rounds failed once (`2026-10-14T17-45-34-codex`): the
  builder moved the card to Doing before blocking it, following work-on-card's "with the card yours in Doing". card-loop
  now says to block it where it is; run again, it passes for both (`2026-10-14T17-49-32-codex`,
  `2026-10-14T17-50-55-claude-code`).

## A decision put to the user without a "?" counts: fakes, Codex rescored, fixtures v53, 11 October 2026

#566: every **mode-*-plans**' "wrote cards for alpha, or asked first" and "surfaced a decision for the user" looked only
for a `?`. A request to choose now counts too ("Please choose…", "Let me know which…", "I need your decision on…"); a
polite closing ("Please let me know if you need anything else", "Tell me if anything is unclear") doesn't. Fixtures v53
(v52 on the lane's branch, before #374's v52 merged).
- **Fakes**: the four mode-*-plans pass as before (`2026-10-11T10-14-53-fake`); both checks are skipped for the fakes,
  which act nothing out there.
- **Codex rescored, no new trial**: the one model trial of these on record (`2026-10-10T23-50-39-codex`,
  mode-coordinator-plans) ended "Please choose the export target and contents above…" with no cards. It failed both
  checks before and passes them now. It was the only saved trial whose result changes.

## Merging through the merge slot: fakes, Codex (its default model, `gpt-5.6-luna`), fixtures v51 (v52 once merged with main), 11 October 2026

#374 checks that merge-ready's merge slot is used, from what ran rather than mentions. The evidence:
- Hive's own record (`HIVE_TEST_MERGE_SLOT_LOG`, development builds only): each change to the slots (who holds one,
  told so or not, and who waits) and each claim or release as Hive resolved it (the branch, and what it did), timed.
- The checks' own runs: check.js records each run's start (commit, base, any merge in progress, and the tree it
  checked: the tracked files as they are on disk, staged or not) and its end with the result. What went into a merge is
  the run that checked exactly the tree the merge committed, so a file changed after the checks doesn't count.
- The merge's moment: a reference-transaction hook in the scenario's repository times each branch update to the
  millisecond, from prepared to committed.

**merge-main-moved** keeps #306's base-moved checks and adds:
- the agent's claim of the base's slot held;
- it held the slot from before the checks that went in until they ended passing;
- it merged in the same hold, after the checks;
- its own release of the base's slot ended that hold after the merge.

New:
- **merge-slot-queued**: Implementer, running, holds the slot until Coder is in line behind it. Coder waits, holds the
  slot only after Implementer's release, then checks, merges and releases.
- **merge-checks-fail**: the branch fails its checks. The agent held the slot through the failing run (on the branch,
  or with its merge in progress in the base), merged nothing, and released the slot itself after.

A hold that ended otherwise (its session's end, the user), a release resolved to another branch (#586's bare
`release` after a checkout) or a no-op, and a time that can't be placed (a check that never ended, a merge git kept no
time of) don't count. `tests/scenarioObserve.test.ts` fails each check on its own with a real repository: no slot use,
never released, released by cleanup, by a release for another branch or a no-op, released between the checks and the
merge within the same second, released while the checks ran, a check that never ended, another branch's slot, a hold
only after the checks, a turn not taken, never in line, a failing branch merged anyway, and a staged merge changed after its checks passed and then
committed. It also passes the staged workflow (`git merge --no-commit` in the base, the checks there, then commit or
abort).
- **Fakes**: baseline `before-374` (v50, on 9fce652: merge-main-moved 4/4, merged-to-done 1/1) and `after-374` (v51,
  first round: merge-main-moved 8/8, merge-slot-queued 9/9, merge-checks-fail 5/5, merged-to-done 1/1). Same guidance
  revision (`69388e8bab64a2cf`) and launch size (1,947 bytes core); the slot calls add 2 or 3 tool calls (107–190 bytes)
  a scenario. The fake's release naming no branch after it checked out its branch fails "released the slot itself" in
  merge-checks-fail (it resolves to `feature`), and passes in merge-main-moved (back on the base).
- **Codex, its default model** (CLI 0.162.1): on the first round's evidence (`2026-10-11T08-35-35-codex`, $0.15), all
  three passed. Those records have no call records, ref times or check ends, so they were run again on the final
  evidence (`2026-10-11T09-10-31-codex`, $0.13). merge-main-moved passed every check. merge-slot-queued passed every slot check: it waited in line, staged the merge in the base with `--no-commit`, checked it, committed and released. Only "read the merge-ready skill" failed: it read no skill. merge-checks-fail claimed no slot this time: it staged the merge, saw the checks fail, aborted and merged nothing, so the three slot checks and the skill read failed. Models vary from sample to sample, and the first round's sample did use the slot here. Those records have no checked trees, so they can't show that what went in was what was checked. Run again on the final evidence (`2026-10-11T09-28-17-codex`, $0.16): every slot check passed in all three, the tree its checks ran on is the tree each merge committed, and only merge-checks-fail's "read the merge-ready skill" failed.
- **Codex, `gpt-5.6-luna`** (`2026-10-11T08-31-38-codex`, $0.015, first round): read no skill and claimed no slot. It
  merged at once in merge-main-moved (the base-moved checks fail too, as at v50) and merge-slot-queued, and in
  merge-checks-fail ran the checks on the base and merged the broken branch. That is a model skipping merge-ready, not
  a fixture change.
- **Claude Code**: not run. Its test home's sign-in had expired (`claude auth status`: not logged in), and the trial
  ended as "the session ended" rather than an environment skip (#577).

## Reports and verdicts lead with a one-line summary: fakes, Codex (its default model), fixtures v46–v47, 11 October 2026

#532: work-on-card has a report to Review start with a one-sentence summary, review-agent-work a verdict with one line
("Round 1: FAILED: 2 findings: …"); `hive_read_task` with `summary: true` gives each comment as its first line, and
card-loop and run-lanes read wakes that way when the gist is enough. Fixtures v47 add a check to **work-on-card** (its
report leads with a summary line, 10–300 characters) and **review-card** (its verdict's first line, the same, says
passed or failed); their fakes post that comment through `hive_update_task`.
- **Fakes**: before `hb1-532-before` (v46 on 4d7a16a, `2026-10-11T07-33-37-fake`) 76 of 76; after (v47,
  `hb1-532-after`, `2026-10-11T08-02-47-fake`) 76 of 76. Hive's cost changed only in the two scenarios whose fakes now
  comment through a hive tool (0 → 91 characters, 1 call each); every other scenario is unchanged.
- **Codex: 4 of 4 pass** (`2026-10-11T08-27-42-codex`, $0.221): work-on-card and review-card pass their new checks
  (the report and the verdict lead with a summary line); card-loop-rounds and coordinator-wake-failed pass. It didn't
  read with `summary: true` in these runs (coordinator-wake-failed read the latest comment in full): the reports here
  are short, and the skills offer it when the gist is enough.
- **Claude Code**: not run: its test home isn't signed in.

## The Assistant watches whole lanes: fakes, Codex (its default model), fixtures v46, 11 October 2026

#531: `hive_wait_for_tasks` with `lanes` (ids, or `["all"]`) is a lane watch: every running lane, followed as it goes on,
no card limit, woken only for a failed review, a blocked or stalled card, a lane due to merge, ended or abandoned.
run-lanes and coordinate-agents now say to watch the lanes that way, and the lanes-running tail and `hive_lane start`'s
nudge point at it. Fixtures v46: the coordinator scenarios' fakes watch `lanes: ["all"]`, and a lane watch on all
lanes counts as covering every lane's cards (`watchCovers`); coordinator-lanes-to-end's first-wake check also takes a
lane watch's own line.

**Before and after** (Performance → Compare calls v45 against v46 not comparable, so per scenario here):
- **Fakes**: before `hb1-531-before` (v45 on a7b9e6e, results `2026-10-11T05-42-20-fake`): 76 of 76. After (v46,
  `2026-10-11T06-16-02-fake`, baseline `hb1-531-after2`): 76 of 76. Hive's cost changed only in the coordinator
  scenarios, whose fakes now watch lanes: after round 2 trimmed the lane watch's reply (the events only when not the
  default), each is smaller than before (`2026-10-11T06-47-53-fake`): coordinator-team-lanes 640 → 624 characters,
  wake-failed 554 → 534, wake-question 336 → 316, reassign 735 → 721, lanes-to-end 762 → 734; the same calls and
  requests, the same guidance.
- **Codex, 4 of 4 both times**: before (a7b9e6e, v45 fixtures, `2026-10-11T06-09-37-codex`, $0.252) it watched cards
  (`{"cards":[2,3,1],…}`, the lanes' cards listed); after (v46, `2026-10-11T06-41-15-codex`, $0.235) every last watch
  was `{"lanes":["all"],"wake":true}`. Hive's cost: team-lanes 6,304 → 4,349 characters (17 → 18 requests), wake-failed
  3,285 → 4,518 (10 → 9), wake-question 1,460 → 1,495 (7 → 7), reassign 6,501 → 5,782 (27 → 21); one sample each.
  Round 1's after run (`2026-10-11T05-01-03-codex`, $0.255) was also 4 of 4 with lane watches.
- **Claude Code**: not run: its test home isn't signed in.

## The Assistant leaves a message for a busy agent: fakes, Codex (its default model), fixtures v44–v45, 11 October 2026

#530: `hive_message_agent` leaves a watching or busy agent a message (typed at once into an idle or watching agent, its
watch carrying on; else with its next line, at the front of a wake that comes first), and coordinate-agents and run-lanes
say to use it rather than ask the user to paste. Fixtures v45 add **assistant-message-watching** (Coder reviews a card in
its loop and watches for it; the user's answer to the card's question is to reach Coder: it is passed by message, with no
new task, stop or request to paste, and Coder's watch carries on).
- **Fakes**: baseline `hb1-530-before` (v44 on main a669fc1 with the #530 code but its old tool descriptions and skills):
  75 of 75 pass. After round 1 (`hb1-530-after`, results `2026-10-11T01-09-28-fake`): 76 of 76, and no scenario's Hive
  cost changed but the new one's. After round 2's tool description (v45, `hb1-530-after2`, results
  `2026-10-11T02-23-02-fake`): 76 of 76.
- **Codex: 3 of 3 pass**, twice: round 1 (`2026-10-11T01-34-39-codex`, $0.149) and round 2
  (`2026-10-11T02-49-45-codex`, $0.202): assistant-message-watching, assistant-reply-decision (records the decision and
  doesn't message Coder, which has the answer), assistant-agent-watch. In the new scenario Codex also recorded the
  answer on the card and watched it.
- **Claude Code**: not run: its test home isn't signed in.

## Coordinator out of the box: fakes, Codex (its default model), Claude Code (sonnet), fixtures v43, 10 October 2026

#402 (Darren's decisions: adaptive habits, the team material in its own skill) folds the coordinator playbook into the
bundled guidance: a new Assistant skill **run-lanes** (lanes by files, builder and reviewer briefs, **one watch over the
whole team**: every unfinished lane's last card and any card in Review, waiting for the user or at a merge point, on any
change; a board sweep and the whole watch started again on each wake; changing a running lane; verifying claims);
**coordinate-agents** gains "Fit the setup" (light for one or two agents, run-lanes for three or more, pairs or
worktrees, or a wake about a card in a running lane; a one-line suggestion at most), the Done wording (the agent moves its
own merged card; the Assistant only when asked), "one watch at a time: a watch you start again lists everything you
still follow", and, while an agent asks the user, "before you end your turn, start your watch again over the other
work"; the **Coordinator** mode puts watching and verifying first. Hive's reply to the Assistant's `hive_lane start`
says when no watch of its covers the lane's last card.

Scoring (round 2, after HR1's review): a watch check reads the Assistant's **live watch** at the end of its turn (the
session's `watch`: a new watch replaces the last, so an earlier call proves nothing), which must cover the named cards on
any column move. Scenarios, with #325's scoring: **coordinator-team-lanes** (four agents, two lanes: run-lanes read, each
builder and reviewer briefed with card-loop, its cards and partner, ends its turn watching both lanes' last cards, no
"they'll tell you"), **coordinator-wake-failed** (woken by a failed review: reads it, sweeps, watches both lanes' ends
again, gives no verdict and writes no review card), **coordinator-wake-question** (woken by an agent's question: passes it
on, answers nothing, and watches both lanes again, the other lane too), **coordinator-reassign** (a card moved between
running lanes), **coordinator-follow-up** (a complete card placed in the lane owning its files) and
**coordinator-lanes-to-end** (both lanes followed through Hive's real wakes: Builder2's lane ends while it watches, it is
woken, sweeps and watches Coder's lane; that ends, it is woken again and says both are done). Every **mode-*-plans**
checks its cards are complete (80+ characters) and a decision reaches the user, and every **mode-*-coordinates** that one
card on one agent reads no run-lanes and starts no lane. The fixtures' lane agents aren't running, so nothing is in Doing
unless a scenario needs it; v38 makes coordinator-wake-question's lanes run as in life (Coder started and idle after
asking, Builder2 working on #3): with nothing running, Codex read both lanes as stalled and offered to restart Coder
rather than watch. The harness now stops what still runs from a scenario's folder after Hive closes (a command Codex
started through hive-progress outlived its session and held the folder, crashing the runner: Non-shipping #542).
- **Fakes**, v37 (baselines `hb1-402r2-before`, the fixtures on the guidance and code before #402, and `hb1-402r2-after`;
  results `2026-10-10T14-25-39-fake` and `2026-10-10T15-25-55-fake`): before, coordinator-team-lanes can't read
  run-lanes (it doesn't exist); every other scenario passes. After, all pass, lanes-to-end included (it acts out the two
  wakes). Performance → Compare: comparable, 53 **No change** (the agents' scenarios), 21 **Larger** (one sample a
  side): the Assistant's launch guidance is 696 bytes larger in Coordinator mode (the mode's habits, run-lanes in the
  skills' catalog) and 266 in the other modes (the catalog). v38's wake-question passes on the fakes
  (`2026-10-10T16-47-16-fake`). v39 makes lanes-to-end count an idle Assistant as its turn ending only once the
  wake's turn was seen working, or after three idle polls (once, after main was merged, it read the moment Hive types a
  wake in as the end); it then passed 4 of 4 on the fakes (`2026-10-10T19-59-35-fake` to `…T20-01-01-fake`).
- **Codex, before** (v37, `2026-10-10T15-06-00-codex`, $0.33): team-lanes briefed all four and ended watching both lane
  ends, but had no run-lanes to read; **wake-failed** ended watching #1 and #2, not Builder2's lane; **wake-question**
  ended its turn with no watch; **lanes-to-end** never watched both lanes and timed out with both still running;
  reassign and follow-up pass.
- **Codex, after** (v37, `2026-10-10T16-11-15-codex`, $0.59): team-lanes, wake-failed, reassign, follow-up and
  **lanes-to-end** (all six checks: two real wakes, a sweep, both lanes ended, the user told) pass, as do
  assistant-dispatch and assistant-new-lane. **wake-question** with the lanes not running ended with no watch (1 run here,
  3 more with the sharper "start your watch again" line, `2026-10-10T16-25-48-codex`, $0.12: 0 of 4 watched both lanes;
  it read both lanes as stalled). With v38's running lanes (`2026-10-10T16-50-01-codex`, 3 runs, $0.11) it passed the
  question on and answered nothing in all 3, and ended every turn watching both lanes: once on both lanes' last cards
  (the check passes), twice on the asking card #1 and Builder2's running #3 (both lanes covered, but not by their last
  cards as run-lanes says: the check fails). Samples, not rates.
- **mode-coordinator-coordinates under Codex** fails "launched in Coordinator mode": the check reads Claude Code's
  instructions file, which a Codex launch doesn't write (Non-shipping #520). Its other checks pass (no run-lanes and no
  lane for one card).
- **Claude Code**: not run: its test home isn't signed in. Codex spend for #402: about $1.84 in round 1 and about $1.15 in
  round 2 (two runs that crashed on a held folder before #542's fix aren't counted).

**Round 3** (HR1's second review: the strict end-card check kept; Claude Code's test home available). Fixtures v40
score a watch by what it wakes on: column moves, comments and verdicts (a column-only watch misses a question and a
failed review left in Review), and a board sweep only when it comes after the first watch (a wake's turn). v41 runs the
lanes in lanes-to-end too (both builders working on their current cards) and its setup helpers fail the scenario
(`setup: …`) when an agent isn't ready or working, with the environment problem when the screen shows one (they had
answered Claude Code's trust question on the raw screen and with Down then Enter, which can quit it, #218: Builder2's
"exited 1"). The harness stops only what is the scenario's own: its Hive's process tree (taken before it closes, by pid
and start time) and what names its folder at a path boundary (never `scenario-2`'s) and started after it
(`tests/e2e/folderProcesses.cjs`). Guidance: run-lanes says a lane's last card stays in the watch while an earlier one
waits for the user; coordinate-agents' question bullet, the one Codex reads on a wake, says "each running lane by its
last card (run-lanes)". Product: the Assistant's card wake ends, while lanes run, with "Lanes are still running
(hive_lane list): before you end your turn, watch them all again in one watch, each lane by its last card
(run-lanes)." (v42 checks lanes-to-end's first real wake says so; v43's simulated wakes end the same way).
- **Codex, question wake, strict end-card check:** v40 (coordinate-agents without the end-card words) 1 of 3, watching
  the asking card #1 and #3 (`2026-10-10T20-18-12-codex`, `…20-19-15…`, `…20-20-12…`, $0.11); v41 with them 3 of 3
  (`…20-36-21…`, `…20-37-16…`, `…20-38-07…`, $0.12); v42 (the simulated wake not yet ending as Hive's does) 1 of 3
  (`…20-48-05…`, `…20-49-25…`, `…20-50-09…`, $0.12); v43 3 of 3 (`…20-54-51…`, `…20-55-39…`, `…20-56-26…`, $0.14).
  Every run passed the question on and answered nothing. wake-failed v43 passes (`…20-57-14…`); lanes-to-end with
  running lanes passes, v41 and v42 (`…20-41-11…`, `…20-50-59…`).
- **Claude Code (sonnet), question wake** v41, the lanes running (Builder2 working, Coder idle): 0 of 3 ended watching
  (`2026-10-10T20-38-55-claude-code`, `…20-39-33…`, `…20-40-15…`, $0.27): it read no skill on the wake, passed the
  question on and said its watch had ended, then stopped. That is what the lanes-running wake tail is for; its test
  home's sign-in then expired ("Login expired · Please run /login"), so the v43 runs stopped at setup, reported as the
  environment (`…20-58-08…`, `…20-58-53…`), and lanes-to-end under Claude Code too (`…20-43-06…`). HR1's earlier
  Claude run of lanes-to-end (v38 fixture) passed 6 of 6. Claude Code with the tail: to run once the home is signed in.
- **Fakes**: every coordinator scenario passes on v43 (`2026-10-10T20-53-34-fake` and the runs before it).
- Round-3 model spend: Codex about $0.80, Claude Code about $0.52.

## The Assistant lists lanes at Look: fakes, Codex (its default model), fixtures v35, 10 October 2026

#500 (Darren's decision: at Control level Look the Assistant can list lanes, a read): `hive_lane` joins the Assistant's
tools at every level (`ASSISTANT_LANE_TOOLS`), and its description at Look and advise says only list works; the Agent
API already refused start, join and end below Control agents (403). Fixtures v35 add **assistant-look-lanes** (Look, a
running lane, "which lanes are running and where are they?": it lists the lanes, starts or ends none, and names the
lane's current card).
- **Fakes** (baselines `hb1-500-before`, the v35 fixtures on the code before #500, and `hb1-500-after`; results
  `2026-10-10T08-41-53-fake` and `2026-10-10T10-06-29-fake`): 68 of 68 pass both times. Performance → Compare:
  comparable, 68 **No change**. The fake doesn't check Claude Code's permission list, so it can't show the gap.
- **Codex: 2 of 2 pass** (`2026-10-10T10-28-46-codex`, $0.084): assistant-look-lanes and assistant-new-lane. On the old
  code assistant-look-lanes passed too (`2026-10-10T09-01-01-codex`): Codex doesn't gate Hive's tools by the
  Assistant's trusted list, so the gap was Claude Code's (a permission prompt at Look).
- **Claude Code**: not run: its test home isn't signed in.

## Card-loop rounds and wait as settings: fakes, Codex (its default model), fixtures v34, 10 October 2026

#412 (Darren's decision: Rounds 10, Wait 6h, set per workspace, a project can override, a prompt's own values win): a
lane started without rounds or a wait takes the project's, else the workspace's settings. card-loop gives `hive_lane
start` only the values its request named and uses the lane's from the reply; coordinate-agents briefs a lane with rounds
and a wait only when the user gave them. Fixtures v34 add **card-loop-lane-defaults** (the workspace's settings 7 and
3 h, a prompt naming neither: the lane has 7 and 180 minutes, and the verdict watch waits 180) and
**card-loop-lane-override** (the same settings, a prompt with "Rounds: 3. Wait: 1h.": 3 and 60).
- **Fakes** (baselines `hb1-412-before`, the v34 fixtures on the code and skills before #412, and `hb1-412-after`;
  results `2026-10-10T07-30-17-fake` and `2026-10-10T07-49-28-fake`): before, the two new scenarios can't set the
  workspace's settings (no `workspace:setLoops` yet); the other 63 pass. After, all 67 pass. Performance → Compare:
  comparable, 65 **No change**, the two new ones incomplete (no before sample).
- **Codex: 6 of 6 pass** (`2026-10-10T08-08-30-codex`, $0.41): card-loop-lane-defaults (7 rounds, a 180-minute wait),
  card-loop-lane-override (3 and 60), card-loop-lane, card-loop-lane-join, card-loop-rounds and assistant-new-lane.
- **Claude Code**: not run: its test home isn't signed in.

## Hive wakes a loop's reviewer and builder: fakes, Codex (its default model), fixtures v33, 10 October 2026

#405 (Darren's decision: on by default for cards with a reviewer, with a per-project opt-out): Hive wakes a card's
reviewer when it arrives in Review and its builder on a verdict, with no card watch of theirs (`main/loopWakes.ts`).
card-loop gains a paragraph: Hive may wake the agent itself, act on that line as on a watch's, and watches are still how
it waits. Fixtures v33 add **card-loop-loop-wake** (a reviewer with no watch given Hive's loop-wake line reviews the card
and waits for the next).
- **Fakes** (baselines `hb1-405-before`, the v33 fixtures on the code and skill before #405, and `hb1-405-after`;
  results `2026-10-10T05-47-46-fake` and `2026-10-10T06-06-47-fake`): every check passes both times; Performance →
  Compare: comparable, all 65 **No change**.
- **Codex: 5 of 5 pass** (`2026-10-10T06-25-12-codex`, $0.35): card-loop-loop-wake reviewed the card and ended watching
  the next; card-loop-blocked, card-loop-return, card-loop-recurring-review and card-loop-rounds pass with the new
  paragraph too.
- **Claude Code**: not run: its test home isn't signed in (as for #481).

## A blocked card stays in its loop: fakes, Codex (its default model), fixtures v32, 10 October 2026

#481 (Darren's decision: a blocked card stays in its lane, paused; the reviewer never drops it): a card that becomes
blocked no longer leaves an agent's watch (#420 released it, so on #468 the reviewer dropped a card its builder had
blocked to ask a question, and nobody reviewed it when it came back). card-loop says a blocked card is paused, not gone:
the loop doesn't take the next card meanwhile. Fixtures v32 add **card-loop-blocked**, #468 replayed: the reviewer has
just failed #1 and waits for its next round; once it is watching, its builder blocks #1 to ask the user, 15 s later
unblocks it and returns it to Review; nobody prompts the reviewer, and it must review #1 (woken by Hive) without moving
on to #2. The harness gained `fakeWakes` (the fake Claude Code's answer to a wake) and `fakeSkips(provider)`.
- **Fakes** (baselines `hb1-481-before-v32`, the v32 fixtures on the old watch code and skill, and `hb1-481-after-v32`;
  results `2026-10-10T04-32-47-fake` and `2026-10-10T05-01-38-fake`): before, card-loop-blocked **fails** as #468 did
  (the block ends the watch, "Ended Coder (alpha)'s watch on it: the card is blocked", and the returned card is never
  reviewed); after, all 64 pass. Performance → Compare: comparable, 63 **No change**, card-loop-blocked incomplete (its
  before sample timed out).
- **Codex, on the old code: card-loop-blocked fails** (`2026-10-10T04-56-06-codex`, $0.051): released by the block, the
  reviewer moved on to #2 and never reviewed #1.
- **Codex, with #481: 2 of 2 pass** (`2026-10-10T05-19-49-codex`, $0.15): card-loop-blocked reviewed #1 once Hive woke
  it, without moving on first; card-loop-released still drops a reassigned card and goes on. Under v31 (the scenario
  without the block mid-watch) card-loop-rounds and card-loop-recurring-review passed with it too
  (`2026-10-10T03-49-51-codex`).
- **Claude Code (sonnet)**: not run: its test home isn't signed in (`2026-10-10T05-22-30-claude-code`, skipped for the
  environment).

## A bulk board change is one change: fakes, Codex (`gpt-5.6-luna`), Claude Code (sonnet), fixtures v29, 9 October 2026

#488 (Darren's decision): the Assistant's `hive_update_tasks` counts as one of its 30 changes for a message, however
many cards it has, so a bulk move never stops part-way. Hive enforces it (`assistantControl.admit`); the coordinate-agents
skill's "Bulk moves" line and the tool's description now say so instead of "each card counts".
- **Fakes** (baselines `b3-488-before` on `540fbd2`, clean, and `b3-488-after`, the change uncommitted; results
  `2026-10-09T22-01-58-fake` and `2026-10-09T22-39-09-fake`): every check passes both times, and Performance → Compare finds all
  61 scenarios **No change** (the description is shorter by a sentence, within 1%).
- **Codex: 2 of 2 pass** (`2026-10-09T22-23-11-codex`, $0.013): assistant-bulk-move moved the five cards with one
  `hive_update_tasks` call; assistant-dispatch started and followed its card.
- **Claude Code (sonnet)**: assistant-bulk-move **passes** (one call, $0.114). assistant-dispatch fails "the agent did it"
  (the card still in Doing when the run ends, after the Assistant started it and watched it), three times, **also without
  this change** (`22-57-43`, on `540fbd2`): not from #488, now #498.

## Asking before taking the card: fakes, Codex (`gpt-5.6-luna`), Claude Code (sonnet), fixtures v29, 9 October 2026

#438 (Darren's option 3): work-on-card has an agent take the card (move it to Doing, which gives it to itself) before it
asks the user a question about it, and clear `blocked` once a decision answers it. A card counts as an agent's for the
decision line (#401) only in Doing with it, so a question asked with the card in Todo left the decision nobody's.
Fixtures v29 add **decision-before-taking**: decision-while-waiting with the card in Todo and no agent, the decision
recorded once the turn ends wherever the card is.
- **Before, a model** (old skill, results `2026-10-09T19-55-23-codex` and `-claude-code`): **Codex failed** exactly as the
  card says: it read the skill and the card, asked, and left the card in Todo with no agent, so Hive told no one and it
  never carried on. **Claude Code (sonnet) passed**: it moved the card to Doing before asking.
- **After** (`2026-10-09T19-58-54-codex` and `-claude-code`; decision-before-taking, decision-while-waiting,
  work-on-card and card-decision): **Codex 4 of 4** ($0.071) and **Claude Code 4 of 4** ($0.397). In
  decision-before-taking both took the card before the decision, were told once, read the card, wrote "Welcome back!"
  and moved the card to Review.
- **Fakes** on one source (`7ce2a15` plus the change), the before run with only work-on-card put back (baselines
  `b3-438-before-v29` and `b3-438-after`, results `2026-10-09T20-49-26-fake` and `2026-10-09T20-31-25-fake`): every
  check passes both times, and Performance → Compare finds all 61 scenarios **No change** (the guidance revision, tool
  list and replies are unchanged; the skill grows by one step). A v28 baseline before the scenario was added
  (`b3-438-before`) isn't comparable with v29 runs.

## Hive sets the agent's folder: no git worktree of its own; fakes, Codex (`gpt-5.6-luna`), Claude Code (Haiku, Sonnet), fixtures v27–v28, 9 October 2026

#476 adds one line to agents' session contract; #482 (Darren) made a worktree the user asks for theirs: "Hive sets your
folder: make no git worktree to work in unless the user asks (else ask for an agent with its own). Merge or remove a
subagent's worktree before you finish." **worktree-isolation** checks that the agent makes no worktree of its own (git's
list unchanged), leaves the project folder as it was and leaves the board alone.
- **v27** asked outright for "a separate git worktree on a new branch". Without the rule every model made one (Codex 2 of
  2, `2026-10-09T13-58-13-codex`; Haiku 2 of 2, `2026-10-09T13-57-15-claude-code`). With the first wording ("don't make
  git worktrees to work in") Codex made none (`2026-10-09T14-32-41-codex`), Haiku still did (2 of 2,
  `2026-10-09T14-31-39-claude-code`), and Sonnet made none in 1 of 2 (`2026-10-09T14-33-52-claude-code`). Asking
  outright is now the user's call (#482), so v28 tests the agent's own initiative instead.
- **v28** asks it to "keep this folder exactly as it is while you try it", with no worktree mentioned. All runs below had
  no source change while they ran.
  - **Fakes**: without the rule (`baselines/b1-476-before-v28`, guidance `c484fe62…`) and with it
    (`results/2026-10-09T15-15-56-fake`, `985744b0…`), 187 pass and 43 skip both times, check for check. Performance →
    Compare: no regressions, no change in quality, each agent launch +171 bytes of guidance (43 launches), nothing else
    outside the spread.
  - **Model trials**, 2 samples each, without the rule and then with it: Codex `gpt-5.6-luna` (`2026-10-09T15-12-09-codex`,
    `…T15-32-12-codex`), Claude Code Haiku (`…T15-13-28-claude-code`, `…T15-33-54-claude-code`) and Sonnet
    (`…T15-14-27-claude-code`, `…T15-34-51-claude-code`): every check passed in all 12 samples ($0.25 in all). Asked only to
    keep the folder as it is, none made a worktree on its own even without the rule, so these trials show the rule costs
    nothing and changes nothing here, not that it is needed: it stays for agents that would (a subagent's isolation, an
    agent told to work on several things at once).

## A watch already met answers at once; a reviewer asks for the next round: fakes, Codex, Claude Code (Haiku), fixtures v25–v26, 8 October 2026

#434 makes a card watch whose column condition already holds answer at once, also one for a move into the column (a
builder's "verdict, or into Passed" on a card already in Passed had waited six hours). The reviewer's wait for a failed
card's next round now asks for it with `fresh: true` (`hive_wait_for_tasks`, `POST /v1/tasks/wait`), and card-loop's
reviewer step says so. Fixtures v25 (v26 once merged with main) give **card-loop-recurring-review** a check that the reviewer ends its turn watching
for the card to come back (its fake watches with `fresh` before failing it).
- **Fakes**, v25, before (`2867cd2` with the final fixtures) and after, neither source changed while it ran (baselines
  `b2-434-before` and `b2-434-after`): 57 of 58 before, the new check failing (the old code ignores `fresh`, so the
  watch answers Already and the reviewer ends its turn not watching); 58 of 58 after. card-loop +50 bytes; the tool list
  +6.4 KB over the whole run (the `fresh` argument and its sentence).
- **Codex: 6 of 6 pass** (its default model, CLI 0.161.0; `2026-10-08T18-46-06-codex`, $0.398): card-loop-recurring-review,
  card-loop-return and card-loop-already-in-review, twice each; the reviewer ended its turn watching with `fresh`.
- **Claude Code (Haiku): 6 of 6 pass** (CLI 2.1.294; `2026-10-08T18-52-08-claude-code`, $0.055): the same scenarios.

## A new lane in a new conversation: fakes, Codex (`gpt-5.6-luna`), fixtures v22–v25, 8 October 2026

#437 gives `hive_prompt_agent` a `newConversation` (the agent's conversation ends, kept in the Sessions tab, and a new
one starts on the task, with no handover), and adds a bullet to coordinate-agents: a new lane's brief goes in one
`hive_prompt_agent` call with `newConversation`, not `hive_start_task`, and the conversation is kept within a lane. The
tool's description gets the parameter's meaning only. Fixtures v23 (v25 once merged with main) add **assistant-new-lane** (Coder idle after its last
lane; "start its next lane on #1"): one call, Coder runs in a new launch and session, and its last conversation stays
listed. The fake Codex now starts on a first prompt given on its command line, as Codex does (it ignored it before, so a
start with a prompt never ran under it).
- **Fakes**: before (`631738f`, v22, baseline `b3-437-before`) and after, neither source changed while it ran: v22 with
  the first wording (`b3-437-after`), every check the same; v23 with the final wording (`b3-437-after-v23`), all 58 pass,
  and the 57 scenarios both ran have the same checks. Sizes: the Assistant's skills +602 bytes (19,481 → 20,083), its
  tool list +167 (22,705 → 22,872); project agents' sessions are unchanged. Merged with main (#430, #401, #426, whose
  fixtures were v24): v25, all 59 pass (`b3-437-after-v25`); the Assistant's skills are 20,173 bytes with #426's line.
- **Codex**: with the first wording, assistant-new-lane **failed** (`2026-10-08T16-32-22-codex`): the Assistant started
  the lane's card with `hive_start_task` (the skill's "A card" bullet), in Coder's current conversation. The bullet now
  says a lane, even of one card, goes through `hive_prompt_agent` with `newConversation`, not `hive_start_task`. Then
  **2 of 2 pass** (`16-38-04`, `16-39-51`, $0.015), and assistant-dispatch still starts a plain card with
  `hive_start_task` (`16-38-04`); assistant-agent-watch passed too (`16-32-22`). After the merge, v25: passes again
  (`17-22-58`, $0.011).
- **Claude Code**: not run (its test home isn't signed in).

## A card that left a loop's watch: fakes, Codex (`gpt-5.6-luna`), fixtures v22, 8 October 2026

#420 releases a card from the watch of an agent whose part in it ended (given to another agent, reviewed by another, or
blocked) with a line ("[Hive] #1 was reassigned to Other (your watch on it ended). Your card watch has ended: drop it from
your list and carry on with your next card."), and adds a line to card-loop: such a wake means drop the card and carry
on, without asking. Fixtures v22 add **card-loop-released** (a reviewer with #1 then #2 gets that line for #1).
- **Fakes**, v22, before (`4d9337a`, with the final fixtures, in a worktree of its own) and after, neither source changed
  while it ran (baselines `b2-420-before` and `b2-420-after`): Performance → Compare finds them comparable, every scenario
  the same, all checks passing both times. card-loop's text read grows +259 bytes; the tool list is unchanged.
- **Codex: 2 of 2 pass** (`2026-10-08T07-55-04-codex`, $0.030): told #1 was reassigned, the reviewer read card-loop, went on
  to #2 (began its review), didn't wait on #1 again and didn't stop to ask; card-loop-rounds still asks at the limit.
- **Claude Code**: not run (its test home isn't signed in).

## The user's replies told to the Assistant: fakes, Codex (`gpt-5.6-luna`), fixtures v21, 8 October 2026

#418 tells the Assistant's watches when the user answers an agent in its pane ("[Hive] The user replied to Coder on #1:
"C, the hive cell"…"), adds a line to coordinate-agents (such a reply is what the user told the agent: don't ask again; a
decision goes on the card), and a clause for the Assistant only in the two watch tools' descriptions. Fixtures v21 add
**assistant-reply-decision** (the Assistant gets that line for a card whose agent asked the user to pick an icon).
- **Fakes**, v21, before (`7456ea1`, #416 without #418, with the final fixtures, in a worktree of its own) and after,
  neither source changed while it ran (baselines `b2-418-before` and `b2-418-after2`): Performance → Compare finds them
  comparable, every scenario the same, all checks passing both times. Sizes: the Assistant's skills +293 bytes, its tool
  list +178 (the clause is the Assistant's only: project agents' tool list is unchanged).
- **Codex: 2 of 2 pass** (`2026-10-08T06-03-45-codex`, $0.021): told the user's reply, the Assistant recorded "C, the hive
  cell" as the card's decision, didn't ask the user again and didn't type it into Coder; assistant-dispatch still passes.
- **Claude Code**: not run (its test home isn't signed in).

## Agent watches: fakes, Codex (`gpt-5.6-luna`), fixtures v19–v20, 8 October 2026

#416 gives `hive_wait_for_agents` a `wake` (an **agent watch**: the Assistant, or an agent, ends its turn and is woken
when an agent finishes, waits for the user or stops), gives the tool to project agents too, and changes coordinate-agents
(an agent watch rather than waiting call after call; a card watch for work on a card) and the Assistant's always-present
line (a watch wakes it too). Fixtures v19 added **assistant-agent-watch** (Coder busy with work that has no card; "tell me
when it's done"): it passes only when the Assistant ends its turn watching (status `watching`), not waiting in the call.
v20 lets assistant-dispatch follow its card with a card watch on that card as well as with `hive_wait_for_agents`.
- **Fakes**, v19, before (main `21c2ff5` with the final fixtures, in a worktree of its own) and after, neither source
  changed while it ran (baselines `b2-416-before-r2b` and `b2-416-after-r2b`): Performance → Compare finds them
  comparable. assistant-agent-watch fails before (main ignores `wake` and holds the call until Coder is done) and passes
  after; every other check is the same. Project agents' tool list grows **+10.3%** (+1,321 bytes a session: the tool is
  new to them); the Assistant's grows +463 bytes (the longer description), its instructions +66 and its skills +352.
  The runs' times went up 2–4 s across the board; three repeats of two scenarios on each side all took 15 s, so that was
  the machine's load.
- **Codex: 2 of 2 pass** under v20 (`2026-10-08T04-23-27-codex`, $0.018): the Assistant read coordinate-agents, watched
  Coder with `wake`, ended its turn watching without polling, and was woken when Coder finished; dispatching a card, it
  followed the card with a card watch. Under v19 (`04-03-07`) assistant-dispatch failed only because its check wanted
  `hive_wait_for_agents` for card work, which the skill now sends to a card watch: v20.
- **Claude Code**: not run (its test home isn't signed in).

## Card decisions: fakes, Codex (`gpt-5.6-luna`, CLI 0.160.1), Claude Code (sonnet), fixtures v18, 7 October 2026

#357 adds a card's **Decisions** and the "new decision" flag on an agent's replies, and changes work-on-card (read decisions
first; read the card again as part of moving it to Review), review-agent-work (a decision the work ignores is blocking),
card-loop (a reviewer back in Review reads the card with `comments: 1`) and coordinate-agents (record the user's decisions
as decisions), plus two tool descriptions (`hive_update_task` `decision`, `hive_read_task` decisions first). Fixtures v16
added **card-decision** and **review-against-decision**, v17 **review-decision-next-round**, v18 loosened card-decision's
model-only file check (it wanted the original `<input name="user">` markup).
- **Fakes**, one source, unchanged while each ran, the before run with only #357's guidance put back (the four skills and
  the two descriptions; baselines `b5-357-before-v18` and `b5-357-after-v18`, results `2026-10-07T13-09-06-fake` and
  `2026-10-07T13-30-28-fake`): the same checks pass both times (154 pass, 40 skipped, 0 fail; the fakes act the decision
  scenarios out by script, so they show Hive's side: the flag in the reply, the board, the costs). The session contract
  and every tool reply are unchanged; the tool list grows **+3.0%** (204,284 → 210,458 bytes over the run); skill text
  read grows +626 bytes in each of the two scenarios that read work-on-card's edited copy.
- **Codex: 3 of 3 pass** (`2026-10-07T13-46-14-codex`, $0.036): the builder read the card again after the decision and
  before Review, the reviewer read the card in full and failed work that ignores the decision, and in round 2 it read the
  card in full before its verdict. (A first try of review-decision-next-round, `12-43-37`, hung for its 6 minutes with no
  tool call after "I'm continuing the card loop…"; it passed when run again, `12-52-39`.)
- **Claude Code (sonnet): 2 of 3 pass** (`2026-10-07T13-44-27-claude-code`, $0.374). Both reviews pass. In card-decision it
  moved the card to Review 6 s after the decision without reading the card again; that reply carried the flag (the card was
  its own when the call began), it read the card at once, changed login.html to match ("Aligned with the new decision")
  and said so, leaving the card in Review rather than moving it back to Doing for the fix. The first trial
  (`12-56-21`, before the flag counted the cards an agent had when a call began) had no flag on that reply and didn't
  notice the decision.

## Long commands get a title: fakes, Codex (`gpt-5.6-luna`, CLI 0.160.0), fixtures v11, 6 October 2026

#251 changed the session contract's hive-progress line to `hive-progress --title "<what and why, in a few words>" --
<command>` (and "shows them to the user"); fixtures v11 added the model-only check **gave the run a title for the user**
to progress-long-command and progress-background. #272 measured it cleanly, on one source (`7030a62`, unchanged while
each run ran), the before run with only that line put back as it was:
- **Fakes** (work-on-card and the three progress scenarios; baselines `b6-272-before` and `b6-272-after`, results
  `2026-10-06T13-48-37-fake` and `2026-10-06T13-50-39-fake`): all pass both times, and Performance → Compare finds them
  comparable. The launch guidance grows **+53 bytes** (1,506 → 1,559 characters of the contract; +41 with wrapping off,
  progress-off), so each scenario reads *Larger or worse*; no check passed or ran less often. Everything else is
  unchanged. The fakes skip both "ran through hive-progress" and "gave the run a title": they show the size, not what a
  model does with the line.
- **Codex: 2 of 2 pass** (`results/2026-10-06T13-52-42-codex`, $0.003), one sample each: both ran
  `hive-progress --title "Run full npm test suite" -- npm test` (the background one through `exec_command` with a 1 s
  yield).
- **Claude Code** (sonnet, CLI 2.1.291, its test home): no result. Claude Code answered the prompt with "Login expired ·
  Please run /login" at once (`2026-10-06T13-54-07-claude-code`; the 6 Oct 02:05 and 00:18/00:24 tries, on 2.1.290, were the same),
  and the harness waited out its 6 minutes. The test home needs signing in again, by hand.

## On Hold and Passed: fakes, Codex (`gpt-5.6-luna`, CLI 0.160.0), fixtures v10, 6 October 2026

#170 adds the On Hold and Passed columns: the session contract, card-loop, review-agent-work, work-on-card, merge-ready and
coordinate-agents now say a reviewer moves a passing card to Passed, Done means merged and On Hold is the user's. Fixtures
v10 replace **standing-done** with **review-passed** and add **merged-to-done** and **hold-skipped**; **review-interrupted**
no longer offers Done, and **card-loop-two-cards**' passed card is in Passed.
- **Fakes**, before (`card170-before-claude` / `-codex` baselines, results `2026-10-05T23-18-53-fake` and
  `2026-10-05T23-20-02-fake-codex`, v9: 35 of 35 pass) and after (`2026-10-05T23-43-40-fake` and
  `2026-10-06T00-06-02-fake-codex`, v10: 37 of 37 pass). The versions differ, so Performance → Compare only shows them;
  over the 34 scenarios both ran: the session contract +5.5% (about 80 characters a launch), skills +1.0%, the hive tools'
  list +2.1%, tool replies unchanged.
- **Codex: 8 of 8 pass** (`results/2026-10-06T00-07-15-codex`, $0.08): work-on-card, review-card, review-interrupted,
  done-card-more-work, **review-passed** (the reviewer moved it to Passed with its verdict), **merged-to-done**,
  **hold-skipped** (took the Todo card, left the On Hold one alone) and card-loop-two-cards.
- **Claude Code** (CLI 2.1.290, its test home): no result. Two tries (`2026-10-06T00-18-23-claude-code`,
  `2026-10-06T00-24-57-claude-code`) timed out with no reply and no tokens used, the environment rather than the change.

## Card loops: Codex (default `gpt-6.1-sol`, CLI 0.160.0), fixtures v9, 5 October 2026

The card-loop scenarios only (#143: wake lines name a dependency's agent and say Done isn't merged; the skill covers
dependency watches, Done ≠ merged and always re-arming), two samples each, on Codex's default model now that #192
prices it (`results/2026-10-05T05-23-51-codex`, $0.55 API-equivalent):
- **Every behaviour check passes, 8 of 8 samples**: rounds asked the user at the limit, recurring went back for round
  three, recurring-review failed it marking the finding as recurring, disputed asked the user.
- **"read the card-loop skill" fails in 7 of 8, a measuring gap, not the agents**: each sample read it, through a
  code-mode script whose output comes back JSON-escaped, which the harness's `name:` line check misses (#198).
- Fake runs before and after the change (`card143-before-claude`/`-codex` baselines, results `2026-10-05T04-49-10-fake`
  and `2026-10-05T04-57-32-fake-codex`): 33 of 33 pass both times; skill bytes +2.5% (the longer card-loop skill).

## Long commands through hive-progress: Codex (`gpt-5.6-luna`, CLI 0.160.0) and Claude Code (default model, CLI 2.1.289), fixtures v9, 5 October 2026

The new **progress-long-command**, **progress-background** and **progress-off** scenarios and **work-on-card**, two
samples each, after the session contract got its hive-progress line (#167; on by default, off in Settings):
- **Codex: 8 of 8 pass** (`results/2026-10-05T02-19-13-codex`, $0.03): `hive-progress -- npm test` in each "on" run (the
  background one through `exec_command` with a 1 s yield, so it went on in the background); plain `npm test` with the
  setting off.
- **Claude Code: 8 of 8 pass** (`results/2026-10-05T02-24-06-claude-code`, $0.86 API-equivalent): the same, through
  PowerShell (the transcript's command doesn't show whether it was run in the background).

## Card loops: Codex (`gpt-5.6-luna`, CLI 0.160.0) and Claude Code (default model, CLI 2.1.289), fixtures v8, 5 October 2026

The card-loop scenarios only (#173), two samples each, after the skill's rounds became "a round is one build and its
review; at **rounds** failed reviews, ask" and stopping to ask became always `hive_notify`:
- **Codex: 8 of 8 pass** (`results/2026-10-05T01-40-53-codex`, $0.10), **card-loop-rounds** 2 of 2 included.
- **Claude Code: 8 of 8 pass** (`results/2026-10-05T01-49-19-claude-code`, $1.52 API-equivalent).

On the way there (Codex, same four scenarios): with the new count but a prompt saying "it is in round 2", one rounds
sample still read it as "do round 2's fix" (`results/2026-10-05T01-20-09-codex`); and **card-loop-disputed** failed
2 of 2 (`results/2026-10-05T00-58-32-codex`): one reviewer found a real new bug (fixture v7's `sync.js` makes three
attempts while the card said "retry three times", now "try up to three times"), the other stopped but asked in a card
comment instead of `hive_notify`.

## Card loops: Codex (`gpt-5.6-luna`, CLI 0.160.0), fixtures v7, 4 October 2026

The card-loop scenarios only (#163), two samples each, against the card-loop skill before and after its "a finding that
comes back" rule ($0.17 API-equivalent in all):
- **card-loop-recurring**, **card-loop-recurring-review**, **card-loop-disputed**: 2 of 2 pass after the change
  (`results/2026-10-04T20-51-42-codex`). The two recurring ones also pass 2 of 2 before it
  (`results/2026-10-04T21-05-26-codex`): this model didn't stop early under the old rule either, so these runs show no
  regression rather than the change's effect.
- **card-loop-rounds** fails 2 of 2 both before and after (`results/2026-10-04T21-01-45-codex`): told *rounds: 2* with
  two failed reviews, the builder sends the card round three instead of asking. By the skill's count (each time it goes
  back to Review after failing) the card has had one round, so the scenario and the skill's counting disagree (#173).

The default Codex model (`gpt-6.1-sol`) has no price in `prices.ts`, so a trial with it reports no cost and the budget
stops the run after one trial: use `--model gpt-5.6-luna`, or `--allow-unknown-cost`.

## Codex (`gpt-5.6-luna`, CLI 0.160.0, its test home, Full access)

**20 of 20 pass** under fixtures v2 (`results/2026-10-03T04-44-06-codex`; $0.18 API-equivalent, on a subscription
plan). Its run has guidance revision `63db94808e669a5e`, the same as now, but two pieces of its provenance can't be
recovered:
- Its source fingerprint (`05380a152540`) was taken by the earlier method, which hashed untracked files' names but not
  their contents, so it can't be matched to the current source.
- Its skill revisions were read before setup, so edited-skill and missing-skill don't record what their sessions were
  given.

It wasn't re-run just to refresh them (no paid re-run for a provenance-only change). The next Codex run records both,
and checks v3's delivery checks. That run included:
- **raw-api**: the script ran, listed alpha's card, was refused for beta, and printed no token;
- **assistant-dispatch**: `hive_start_task` worked, then `hive_wait_for_agents`, and the agent finished the card;
- the three new cases: **pick-up-named**, **done-card-more-work** and **progress-log**.

Under fixtures v1, two Codex runs failed and passed when repeated:
- **review-interrupted**: it moved the card to Done after its review ended, before the wording fix below.
- **edited-skill**: it hung for 6 minutes with no tool calls.

## Claude Code: not yet run under fixtures v2

The trials now run Claude Code only in its own test home (`%LOCALAPPDATA%\hive-test\claude`, never the user's
`~/.claude`). That home isn't signed in yet, so `--provider claude-code` prints a skip. Signing in is a one-time step
by hand (README.md).

The earlier Claude runs (fixtures v1, Haiku, CLI 2.1.288; $2.92 over 4 runs) used the user's own Claude home, so its
skills, plugins and settings were part of the run. They also counted hive calls from the transcript. They aren't a
baseline. They're kept below only for what they showed:

- Once Haiku had read a skill, it followed it: work on a card, reviews, fixes, a standing Done instruction,
  prioritising, pick-up, an edited skill, and the Assistant's dispatch and plans.
- Haiku chose skills from their descriptions less reliably:
  - **wrap-up**: re-ran tests it was told had passed.
  - **lasting-decision**: took "remember for every project" as context for the conversation.
  - **plan-only**: used Claude Code's own plan mode.
  - **missing-skill**: skipped Doing in 2 of 3 runs.
- Before the wording fix, it moved an interrupted review's card back to Review and passed it.

## What changed because of the trials

**Guidance**:
- **review-agent-work skill and session contract**: when a card leaves Review during a review, the card is left
  where it is, neither moved back nor on to Done.
- **Board rules**: now separate short lines in the session contract. "Fix or continue" routes to work-on-card.
- **handover skill**: test results the user gives count, so they aren't re-run.
- **split-work description**: also triggers on "how to split work between agents".
- **`hive_start_agent`**: says to use `hive_start_task` for a card.
- **#107**: whether Hive should refuse an agent finishing a card another agent has in Doing (a product decision).

**Harness** (each with unit tests):
- isolated CLI homes;
- the server-side call log;
- strict read evidence;
- token-value checks;
- outcome checks that fail on no-op, failed or out-of-order calls;
- prompts confirmed by the transcript;
- trust questions answered for agents the Assistant starts;
- a fake Codex rollout, so Codex resumes are real.

## Not covered

- **Claude Code under fixtures v2**, until its test home is signed in.
- **Packaged builds.** The trials use the dev build; packaged delivery is covered by `npm run e2e -- packaged-mcp`.
- **The Assistant answering a question an agent asks the user.** A real agent has to reach a question first, which isn't
  deterministic. The tool contract and `coordinate-agents` say never to answer one, and Hive refuses prompts to an agent
  that is waiting.
- **A real npm-installed Codex** (#103 used the fake `.cmd`).
- **Stronger models, and repeat runs for pass rates.** Run with `--model` and `--only` several times when one matters.

## Measured: what each session is given about Hive

From real launches (`node tests/scenarios/measure.cjs`, with the fake CLIs; source `edb813e` with changes
`5baebcf8fd8c`), in UTF-8 bytes; ≈ tokens is bytes / 4 (no tokenizer was run).
- **All 32 combinations** were measured: both providers; the project agent and the Assistant at each control level; a
  short catalog (Hive's own skills) and a long one (40 more of the user's); new and resumed sessions.
- **Every resume was confirmed** from the CLI's own arguments (`--resume <id>`, `codex resume <id>`).
- **Instructions**: for Codex, its developer instructions; for Claude Code, the hive server's instructions plus, for
  the Assistant, its appended prompt.

| Role | Catalog | Instructions | Tools | Skill metadata (skills) | Total | ≈ tokens |
|---|---|---:|---:|---:|---:|---:|
| agent | short | 1,149 | 8,256 | 1,912 (8) | 11,317 | 2,829 |
| agent | long | 1,149 | 8,256 | 7,085 (48) | 16,490 | 4,123 |
| Assistant, Look and advise | short or long | ≈3,250 | 9,769 | 1,197 (5) | ≈14,215 | ≈3,554 |
| Assistant, Control agents | short or long | ≈3,880 | 16,542 | 1,197 (5) | ≈21,620 | ≈5,406 |
| Assistant, Control agents and create projects | short or long | ≈3,950 | 16,804 | 1,197 (5) | ≈21,950 | ≈5,488 |

- **Claude Code and Codex measure the same**, to within 4 bytes (Claude's appended prompt for the Assistant carries
  one more line break).
- **A resumed session measures the same as a new one.**
- **The user's own skills reach project agents only**: the long catalog doesn't change the Assistant's size.
- **The tool schemas are the largest fixed part.**

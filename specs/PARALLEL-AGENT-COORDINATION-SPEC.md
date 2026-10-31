---
doc-type: spec
status: draft
owner: jason
created: 2026-09-22
updated: 2026-10-14
governs: Parallel agent coordination — file-claim manifests and module-boundary decomposition to prevent merge conflicts in multi-agent AFK work
testable: true
compliance: strict
---

# Parallel Agent Coordination

## Problem Statement

When multiple agents work in parallel on independent issues, they may modify the same files — producing merge conflicts that waste agent work or silently break code. Session 2026-09-22 demonstrated this: Streams A (#560) and B (#559) both modified `ship.js` and `prove.js` independently. The merge succeeded because the designs converged, but divergent changes would have discarded one agent's work entirely.

## Design Decisions

| Decision | What | Rationale |
|---|---|---|
| D-1 | File-claim manifest: agents declare target files before starting | Catches overlap at schedule time, not merge time. Cheap pre-flight vs expensive rework |
| D-2 | Module-boundary decomposition: wave planning must check file overlap | Prevention > detection. If two issues touch the same file, they serialize, not parallelize |
| D-3 | Claim granularity is file-level, not line-level | Line-level is fragile (refactors shift lines). File-level is conservative but safe |
| D-4 | Overlap = serialize, not block | Both issues still ship — just not in the same wave. No work is lost |

## Target State

Before launching a wave of parallel agents, a pre-flight check:
1. Each issue's target files are predicted (from spec `governs`, CODE-MAP, or explicit declaration)
2. File sets are compared pairwise across all issues in the wave
3. Overlapping issues are moved to the next wave (serialized)
4. Agents receive their file-claim manifest — they WARN if they touch unclaimed files

Post-wave, an integration check verifies no unclaimed file modifications slipped through.

## Success Criteria

- SC-410: Wave planner predicts target files per issue before agent launch
- SC-411: Pairwise file overlap check runs before wave launch — overlapping issues serialize
- SC-412: Agents receive file-claim manifest in their prompt
- SC-413: Post-wave integration check detects unclaimed file modifications
- SC-414: Module-boundary decomposition rules documented — issue authors check file overlap at creation time
- SC-415: Wave planner uses CODE-MAP.md module boundaries for file prediction when no explicit claim exists

## Implementation Status

| SC | State | Where |
|---|---|---|
| SC-410 | Partial — the plan's union is compared against `discovery.filesToModify` before the first agent spawns, and a discovered file no sub-issue claims **refuses the parallel plan and falls back to single-agent implement** (#751, option 1 of the three the issue named). Chosen over auto-claiming, which hands work to an agent whose brief never mentions it and whose claim audit then passes while the allocation is wrong, and over warn-and-proceed, which is the status quo that spent 2h06m and 2.03M tokens on asaCommandCenter#1585 before SC-413 refused at Commit. An absent or empty discovery list is UNMEASURED and refuses too. Still partial: this is per-issue decomposition, not the cross-issue wave planner the criterion describes | `lib/plan-coverage.ts`; `workflows/ship.js` PLAN-COVERAGE block; `test/plan-coverage.test.ts` |
| SC-411 | Partial — holds within a single issue's sub-issue decomposition, not yet across a wave of issues | `workflows/ship.js` `runDecomposedShip()`; `test/decomposed-ship-dispatch.test.ts` |
| SC-412 | Partial — sub-issue agents receive an explicit "modify ONLY these" file list | `workflows/ship.js` `runDecomposedShip()` |
| SC-413 | Done — the claim travels back with each agent's result and the collection is refused when a worktree reports a file it did not claim, and the six refusals it can emit are pairwise distinguishable. Both staging paths pair the claim through one binding (#627) | `workflows/ship.js` `auditWorktreeClaims()` (COLLECT-CLAIM block), `claimedWorktreeRow()` (CLAIM-PAIRING block), `collectAgentWork()`; `test/collect-claim-enforcement.test.ts`, `test/collect-claim-ownership.test.ts`, `test/claim-refusal-kinds.test.ts`, `test/wave-claim-propagation.test.ts` |
| SC-414 | Not started | — |
| SC-415 | Not started | — |

Issue #66 fixed the disjoint-dispatch path: `runDecomposedShip()` computed the D-2
overlap check and then serialized both branches anyway, while logging that it had
dispatched in parallel. Disjoint sub-issues now run concurrently, and a failing
sub-issue reports its completed siblings rather than discarding them (D-4).

Issue #178 closed SC-413. On run wf_2b3ff032-a4b three of four worktrees modified
`workflows/ship.js`; the claims were correct and disjoint, so SC-411 had nothing to
catch, and SC-412's manifest reached the agents as prose that nothing afterwards
compared the replies against. `claimedFiles` now travels back beside each agent's
`filesChanged`, `auditWorktreeClaims()` refuses any worktree reporting a path it did
not claim — naming the worktree, the path and the claimant — and the groups handed to
the collector are pruned to claimed files, so a contested file can only ever be
written from its claimant's worktree. A missing claim means no claim was issued (the
single-agent and remediation paths) and is unconstrained, except that it still cannot
take a file another worktree claimed.

Still open: nothing coordinates *across* issues or across concurrent human-driven
sessions. That is issue #23.

## A refusal an operator cannot classify (#300, 2026-10-14)

#296 gave `auditWorktreeClaims` three ownership answers and each of them got
its own sentence. Nothing checked that the sentences stay different, and the
sentence is the entire interface. A run dies, the DA reads one line, and what
it does next depends on which kind it was: merge two edits of a shared
registry, write a DA-owned file itself, or send the agent back for exceeding
its scope. Three refusals that read alike cost the same ~75 minutes whichever
one it actually was.

Three properties the test had to get right, and the first two are the ones a
naive version gets wrong:

- **Distinctness is on the SHAPE, not the string.** Every refusal interpolates
  the worktree and the path, so two kinds reported against different files
  differ as strings no matter how identical the wording is. Comparing them raw
  certifies a guard that says `wf_a reported X, which it did not claim` for all
  three. The substituted values are blanked and the comparison runs on what is
  left.
- **Pairwise, and containment as well as equality.** Three `toContain` checks
  that each pass against one generic string is the vacuous assertion
  `.claude/rules/checks-must-be-able-to-fail.md` names. Equality is also not
  the only collapse: if one shape is a substring of another, every `toContain`
  written against the shorter one passes for both.
- **The table is tied to the source.** A per-kind loop only makes a new kind
  impossible to add silently if something counts. Two readings, because either
  alone has a hole — a new push site with a reworded message leaves the
  template count unchanged, and a new arm of an existing ternary leaves the
  push-site count unchanged.

The table grew from the three kinds #300 names to the **six** the block can
actually emit: boundary escape, DA-owned, co-owned conflict, multiple
claimants, and the two arms of out-of-scope unclaimed. Covering what the guard
emits rather than what the issue remembered is the point of counting; the
three named kinds are still asserted by name so the growth cannot drop one.

The out-of-scope wording is pinned by #296 and is asserted verbatim here, so a
later distinctness fix cannot buy green by rewording the message another
criterion holds fixed.

- [x] SC-1432: test/claim-refusal-kinds.test.ts contains [the table covers every refusal the block can emit] — the row count is tied to two readings of the source so a kind added with a reworded message and a kind added as a new ternary arm both fail rather than going uncovered
- [x] SC-1433: test/claim-refusal-kinds.test.ts contains [no two kinds share a message shape] — distinctness is compared pairwise with the worktree and the path blanked out because every refusal interpolates both and two kinds against different files differ as strings however identical the wording
- [x] SC-1434: test/claim-refusal-kinds.test.ts contains [each kind's discriminator appears in exactly one kind's message] — the property an operator uses is that one grepped phrase identifies one kind and a per-kind toContain can never see a token that matches two
- [x] SC-1435: test/claim-refusal-kinds.test.ts contains [could not build the mutant: the co-owned template appears] — the collapse the criterion forbids is performed on a copy of the block and observed so a distinctness check that reads something else is caught and a template that moves aborts instead of no-opping

### What was broken to prove it (SC-1432..1435)

Run and counted over `test/claim-refusal-kinds.test.ts` (21 tests). None is
left in the tree; all were applied and reverted, and every mutation asserted
its target appeared exactly once before writing:

| Mutation | Red |
|---|---|
| the co-owned message replaced by the generic unclaimed one — the defect SC-5 names | 10 of 21 |
| the DA-owned message replaced by the generic unclaimed one | 5 of 21 |
| every refusal rewritten to the one generic sentence | 15 of 21 |
| the co-owned refusal stops naming the worktrees that wrote it | 5 of 21 |
| the pinned out-of-scope wording reworded | 3 of 21 |
| the DA-owned refusal keeps its class but loses its remedy | 1 of 21 |
| a seventh refusal template added with no row in the table | 1 of 21 |

The last two are one apiece by design and are reported rather than hidden:
each is a single named property, and a mutation that turned several tests red
would mean the table's rows were not independent.

## Two validators answered "is this path safe" and agreed only on traversal (#400, 2026-10-15)

Found while verifying SC-3 of #229 before ticking it. SC-3 is satisfied as
written — it asks about *traversal* rejection, and on traversal the two
agreed. The rest of the divergence is this section.

`workflows/ship.js` carried two answers to one question, in two phases:

| | shape | input | checked |
|---|---|---|---|
| `validateFilePaths` | regex set | the raw reported string | STAGING, by `buildSafeGitAdd` |
| `escapesWorktree` | segment walk | a `claimKey`-normalised key | COLLECTION, by `auditWorktreeClaims` |

So the audit accepted a reported path carrying a shell metacharacter, a null
byte, or 500+ characters, reported the run clean, and staging refused it
afterwards — late, in a different phase, with a different message. Nobody was
misled while staging still refused; the cost is that the audit's verdict could
not be relied on, and the next caller to trust it instead of re-validating
inherits the hole. A guard that refuses less than the thing downstream of it
is a guard whose pass means less than it reads.

There is now one table, `CONTRIBUTABLE_PATH_RULES`, and one decider,
`pathRefusal`, in the SECURITY-HELPERS block — the half mirrored by
`lib/workflow-security.ts`, so the mirror keeps covering it. `escapesWorktree`
is gone: it was a second copy of two of that table's rules, and a second copy
survives any mutation of the first.

Three things this had to get right, and the first is the one a naive version
gets wrong:

- **Parity alone is vacuous once the predicate is shared.** With both phases
  calling one decider, removing a rule makes them permissive *together* and a
  pure parity assertion stays green. So every corpus row carries a LITERAL
  expected verdict, written out by hand and derived from nothing, and is
  asserted three times: staging against the literal, the audit against the
  literal, and the two against each other. That is the "red in both
  directions" SC-1535 asks for. It is also #397's and #399's lesson a third
  time — a test parameterised by the thing it checks cannot check it.
- **The corpus is compared on KEYS, not on raw reports.** `claimKey` strips
  the worktree prefix before the audit looks, so `/tmp/wt-a/lib/a.ts` is
  absolute to staging and relative to the audit. That divergence is correct
  and by design (`relativizePaths` exists for it), and comparing those two
  would fail for a reason this is not about. Every row asserts
  `claimKey(wt, p) === p` first, so a row that normalises is caught as a
  corpus bug rather than discovered as a confusing failure.
- **The refusal says which rule, and whether the path is even outside.**
  "not inside its own worktree" is a wrong sentence to print about
  `lib/a;rm.ts`, and an operator who reads it goes looking for a path that is
  not there. The table's second column is `boundary`, and the two refusals it
  selects are a seventh and distinct kind in `test/claim-refusal-kinds.test.ts`.

The two traversal rules are deliberately both present and deliberately
separate. `p.split('/').includes('..')` is the real boundary question; the
regex `/\.\.($|[/\\])/` also matches a segment merely ENDING in `..`
(`lib/foo..`), a legal filename that staging has always refused. Folding it
into the boundary rule would label a legal file an escape; dropping it would
make the audit permit something staging rejects, which is the whole defect.

- [x] SC-1530: test/claim-path-safety-parity.test.ts contains [the corpus is canonical, so the two phases see one string] — every row asserts claimKey leaves it alone, because the audit checks a normalised key and staging checks the raw string and a row that normalises would compare two different strings
- [x] SC-1531: test/claim-path-safety-parity.test.ts contains [staging and the audit refuse the same paths] — one corpus, three assertions per row, two of them against a hand-written literal so a shared predicate that stopped refusing cannot satisfy the parity by making both sides permissive together
- [x] SC-1532: test/claim-path-safety-parity.test.ts contains [a refused path is told which rule refused it] — the refusal names the rule and distinguishes outside-the-worktree from inside-and-unstageable, asserted in both directions so neither sentence can be printed about the other's paths
- [x] SC-1533: test/claim-path-safety-parity.test.ts contains [one predicate, reached by both phases] — the table and the decider are each declared exactly once and the collection block is read for a call into the security block, because a second copy would survive any mutation of the first and the parity would go green for the wrong reason
- [x] SC-1534: test/claim-refusal-kinds.test.ts contains [unsafe but inside the worktree] — the new refusal is a seventh row in the kinds table, so it inherits the pairwise distinctness, containment and discriminator checks #300 built rather than being asserted on its own
- [x] SC-1535: test/workflow-security-integration.test.ts contains [pathRefusal parity] — the inlined decider is driven against the library's over the same corpus, because ship.js cannot import (#69) and a drift in the copy is now a drift in what the audit permits, not only in what staging refuses

### What was broken to prove it (SC-1530..1535)

Run and counted over `test/claim-path-safety-parity.test.ts`,
`test/claim-refusal-kinds.test.ts`, `test/collect-claim-enforcement.test.ts`,
`test/collect-claim-ownership.test.ts`, `test/ship-remediation-commits.test.ts`
and `test/workflow-security-integration.test.ts` (290 tests). None is left in
the tree; all were applied and reverted, and every mutation asserted its
target appeared exactly once before writing.

| Mutation | Red |
|---|---|
| `pathRefusal` refuses nothing | 68 of 290 |
| the audit asks its own narrower question again — #400 restored verbatim | 32 of 290 |
| the shell-metacharacter rule dropped | 28 of 290 |
| the absolute-path boundary rule dropped | 17 of 290 |
| the `..`-segment boundary rule dropped | 9 of 290 |
| the null-byte rule dropped | 7 of 290 |
| the 500-character rule dropped | 7 of 290 |
| the segment-ending-in-`..` rule dropped | 6 of 290 |
| the absolute rule stops being a boundary | 6 of 290 |
| the library mirror drops the shell-metacharacter rule | 6 of 290 |
| both audit refusals collapsed to the boundary sentence | 4 of 290 |
| the library mirror drops the 500-character rule | 2 of 290 |
| `validateFilePaths` in the library keeps its own rule chain | 1 of 290 |

Each rule-dropping row is red on **both** sides — the staging assertion and
the audit assertion for every corpus path that rule covered, plus the mirror
case. That is SC-1535's "both directions", and it is only measurable because
the expected verdicts are literals: had they been read from the predicate,
every one of those rows would be a zero.

The last row is the one worth reading. It is this issue's own defect, met
inside this issue's fix: the first draft added the table and the decider to
`lib/workflow-security.ts` and left `validateFilePaths` *there* still running
its original regex chain, so the file whose subject is "there was more than
one decider" shipped with two. No test could see it — the chain and the table
agreed on every corpus row, so the ship-versus-library parity stayed green.
It surfaced only because the mirror's 500-character mutation scored 1 where
the model predicted 2, and the gap was chased rather than written down. The
guard added for it is a source property, because a behavioural one cannot
exist: two deciders that agree are behaviourally one.

## One staging path paired the claim and the other stripped it (#627, 2026-10-18)

#420 gave a decomposed run a SECOND place that stages agent output: the mid-run
wave commit, so wave N+1's worktrees branch from a checkout containing wave N.
Both it and the end-of-run collect go through `collectAgentWork`, and therefore
through `auditWorktreeClaims`. They did not hand it the same rows.

The audit compares what an agent REPORTED against what the plan CLAIMED, and
the claim is not on the `buildResult` — the agent was never asked to report it
back. It lives on the other half of the settled row, `subIssue.filesToModify`,
and only the pairing on the way back makes SC-412's prose manifest checkable.
The end-of-run path wrote that pairing out inline, twice. `integrateWave` wrote

    accepted.map(r => r && r.buildResult)

which drops `subIssue` on the floor. Every row then reached the audit with no
`claimedFiles`; a wave has more than one participating worktree by definition,
so `SINGLE_WORKTREE_EXEMPT` does not apply, and the fallthrough #296 removed is
gone. The audit's answer is *"no worktree claimed that file"* — for every file
in every worktree. **Every decomposition with a dependency barrier failed
collection, regardless of the work**, with correct and disjoint claims.

Three things this had to get right:

- **One binding, not two agreeing sites.** `claimedWorktreeRow` is declared
  once, in the CLAIM-PAIRING block, and both staging paths call it. Two sites
  that agree are behaviourally one decider
  (`.claude/rules/checks-must-be-able-to-fail.md`, the fourth shape): a
  mutation of either leaves the other holding every case up, and a third
  staging path added later gets written from whichever copy its author read —
  which is exactly how the wave path came to carry a strip instead.
- **The assertion is the CLAIM, not the verdict.** A refused collection can be
  made to succeed without propagating anything, by widening the audit until an
  absent claim permits everything. So every case reads the row list
  `collectAgentWork` was actually handed, and the battery below builds that
  cheap repair and watches the cases stay red under it (the fifth shape, named
  in advance rather than discovered).
- **The fixture is this run's own.** It mints a worktree tree under the OS temp
  directory and names no path from the run that found the bug. A fixture keyed
  on another run's filenames stops witnessing the moment those files move, and
  what is under test is the shape of the handover, not any file in it.

- [x] SC-2058: test/wave-claim-propagation.test.ts contains [the claim reaches the collector through wave integration] — a two-wave plan driven through the real dispatch loop, the real `integrateWave` and the real `collectAgentWork`, asserting the row list the collector was handed carries the plan's claim; the premise that a barrier actually formed is asserted first, so a single-wave plan cannot satisfy it by never integrating
- [x] SC-2059: test/wave-claim-propagation.test.ts contains [one binding pairs a result with its claim, and both staging paths call it] — declared exactly once, called once from the RUN-REF slice and twice from the DECOMPOSED-SHIP slice, with the inline pairing and the strip both counted at zero over the source with comments removed, because this issue's own docblock quotes the expression it replaced
- [x] SC-2060: test/wave-claim-propagation.test.ts contains [three worktrees integrate through a wave rather than the end-of-run collect] — three worktrees with correct, non-overlapping claims, integrated mid-run rather than at the end, asserted on both the rows handed to the collector and the pruned candidates read back off the collect prompt; the paired control is a worktree that exceeds its claim in the same shape, which must still be refused
- [x] SC-2061: test/wave-claim-propagation.test.ts contains [the claim-stripping mutant turns the regression red] — the defect restored verbatim in a copy of ship.js, the suite re-spawned against it, and the reds compared BY NAME; the baseline row is read first, because an empty baseline is an instrument that stopped reporting rather than a clean tree
- [x] SC-2062: test/wave-claim-propagation.test.ts contains [the widened claim guard does not buy the regression green] — the cheapest wrong fix, named before it was built: the claim strip plus a `claimPermits` widened to let an absent claim through. The symptom goes away and the cases stay red, which is the only thing that stops this file certifying the regression it exists to block
- [x] SC-2063: test/wave-claim-propagation.test.ts contains [the fixture is built in a temp tree and names no run's files] — the run id is assembled from parts so the assertion is not itself the occurrence it forbids

### What was broken to prove it (SC-2058..2063)

Run and counted over `test/wave-claim-propagation.test.ts`. The three cases
that spawn the battery skip inside a mutant child, so every row below is out
of 7. None of the mutations is left in the tree; both were applied to copies
under the OS temp directory and `workflows/ship.js` was never modified.

**Baseline, read before any mutation row: 7 pass, 0 fail, 3 skip.**

| Mutation | Predicted | Red |
|---|---|---|
| `claimedWorktreeRow` removed from the wave path — `accepted.map(r => r && r.buildResult)` restored | 2 | **3 of 7** |
| the same, plus `claimPermits` widened to `!Array.isArray(claims) \|\| claims.includes(key)` — the cheapest wrong fix | 2 | **4 of 7** |

The input on which mutant and original differ, named before either count was
believed (#485): a three-worktree wave carrying correct, disjoint claims. The
original hands the collector rows carrying `claimedFiles` and the wave
integrates; the first mutant hands it rows that have none, the audit reports
every file in every worktree unclaimed, and the collection is refused.

**Both rows came back HIGH, and in both cases the extra red is the real kind.**

The first row's third red is SC-2059, the source assertion — the mutant
reinstates the text that case counts at zero. It is about the mutated
behaviour, the file still parses, and the other four cases pass, so this is not
a crashing mutant; it is the source check and the behavioural check turning red
on one change, which is what a binding asserted two ways looks like.

The second row's fourth red is the one worth reading, because it is the whole
argument for writing the cheap fix down. Widening `claimPermits` does silence
the refusal — the collection succeeds again — and the case it breaks is
*"a worktree that exceeds its claim in a wave is still refused"*. So the 5pm
repair for this issue is measurably a disabling of SC-413 for every decomposed
run, and the cost of reaching for it is one MORE red test, not a green suite.

## A refusal with two opposite causes and one sentence (#629, 2026-10-19)

#627 restored the claim to the wave path. What it did not change is what the
audit SAYS when the claim is absent anyway, and `claimant === null` has two
causes that call for opposite next actions:

- **No participant issued a claim at all.** The pairing dropped it — #627's
  defect, or the next one shaped like it. The agent may have been perfectly in
  scope; nothing was ever compared. **Fix the caller.**
- **Participants did issue claims and this file is in none of them.** The
  comparison happened and the agent lost it. **Send the agent back.**

`workflows/ship.js:4402` documented the distinction and
`if (!wt || !Array.isArray(r.claimedFiles)) continue` implemented half of it:
rows with no claim were skipped when building the ownership map, and nothing
downstream remembered that NOBODY had contributed to it. Both ended at *"no
worktree claimed that file"*. An operator reading that line after #627's
failure mode spent the investigation on the agent, and the agent was fine.

Three things this had to get right:

- **The pinned sentence is kept, and the split adds an arm.** #296 SC-3 pins
  *"no worktree claimed that file"* and `test/claim-refusal-kinds.test.ts`
  asserts it by exact equality, so rewording it to make a distinctness problem
  go away is the specific failure that pin exists to catch. That sentence is
  TRUE of the narrower case — worktrees did claim, and none claimed this file
  — so the new arm sits beside it rather than replacing it. The battery below
  measures what the alternative would have cost: the cheapest wrong fix
  rewords it and is 10 red, three of them for that reason alone.
- **An empty claim array is an issued claim.** `claimedFiles: []` is a plan
  that named no files — a planning problem, not a relay one — and reading it
  as "no claim issued" would send an operator upstream after a bug that is not
  there. `Array.isArray` is the same reading `claimPermits` takes one function
  down, so the two cannot disagree about what a claim is.
- **The pair varies exactly one thing.** Two hand-written fixtures can differ
  in something nobody noticed, and then the comparison measures that instead
  of the dimension it names (#585). The second fixture is the first with
  `claimedFiles` deleted, the derivation is asserted before anything is
  concluded from it, and `SINGLE_WORKTREE_EXEMPT` is asserted still to exempt a
  lone agent — because a new refusal arm reachable for one worktree is #228
  reintroduced.

- [x] SC-2114: test/claim-refusal-kinds.test.ts contains [the no-claim arm points upstream and the other does not] — the two absent-claim causes produce distinguishable refusals naming opposite next actions, driven through the real block, with the kind matrix carrying both as separate rows so a third arm cannot be added without one
- [x] SC-2115: test/claim-refusal-kinds.test.ts contains [the pair varies only the presence of claims] — the two fixtures are one fixture and its derivation, asserted equal in every other field first, so the refusal difference can only be explained by the dimension the criterion names

### What was broken to prove it (SC-2114..2115)

Run and counted over `test/claim-refusal-kinds.test.ts`. Every count was
predicted before the battery ran, and **the baseline row was read first** — an
instrument that has stopped reporting takes the baseline down with it, and
that is the row nobody mutates anything to produce.

**Baseline, unmutated: 35 pass, 0 fail.**

| Mutation | Predicted | Red |
|---|---|---|
| the split removed — both causes back under one sentence (genuinely pre-#629) | 7 | **7 of 35** |
| `noClaimsIssued` inverted | 4 | **6 of 35** |
| any participant counts as a claim issuer, so the new arm is unreachable | 6 | **6 of 35** |
| the cheapest wrong fix: one message, with both possibilities appended to it | 7 | **10 of 35** |

**Before believing any of them, the input on which mutant and original
differ** (#485), named and run rather than assumed: two participating
worktrees reporting `gates/workflow.test.ts`, in one fixture carrying
`claimedFiles` and in the other with that key deleted and nothing else
changed. The original answers *"not one of the 2 worktrees in this run issued
a claim at all … Fix the caller"* for the second and *"no worktree claimed
that file"* for the first; row 1's mutant answers the latter for both.

**Two rows came back HIGH and in both the extra reds are the real kind** — the
mutants parse, most cases pass, and every extra red is about the mutated
behaviour.

Row 2's two extras are the sharper ones. Inverting the flag swaps which
fixture gets which sentence, so *"the two out-of-scope arms stay the wording
#296 SC-3 pinned"* goes red — the pin is precisely what a swap breaks. The
other is #300's own `SC-1435` mutant case, which replaces the co-owned
template with the generic sentence and asserts the two shapes collapse. That
case **depends on the unclaimed fixture producing the generic sentence**, and
the inversion moves it. That is a fact about this file worth writing down: it
is a second, independent argument for adding an arm rather than rewording the
pinned one, and it was not visible from the diff.

Row 4's three extras are the pin again plus both halves of `SC-1435`, whose
`loadMutant` can no longer find the generic template in the source and
**aborts loudly** rather than no-opping — the property a mutant builder exists
to have.

**The cheapest wrong fix, named and applied: keep one message and append the
explanation of both possibilities to it** — *"no worktree claimed that file
(either no claim was issued in this run, in which case the pairing dropped it
(#627), or this file is outside every claim)"*. It is the 5pm repair: the
operator is told both things, no branch is added, one string changes.

**The cases do not survive it: 10 of 35 red.** It leaves the two causes
indistinguishable by grep — which is the property an operator actually uses,
one phrase identifying one kind — and it rewords a sentence another criterion
holds fixed. An operator still cannot tell from the line which investigation
to open; they are told that it might be either, which is what they already
knew.

None of the four mutations is left in the tree; all were applied to
`workflows/ship.js`, run, reverted, and the file confirmed byte-identical
afterwards by checksum.

## #906 — the content-comparison arms are each load-bearing, and the registry is total

#892 shipped `overlapReadings()` in `scripts/preserve-worktree-work.ts` and
twenty-one cases over it. #991 measured a five-row battery against those cases
by hand and found one case — titled *"a SIZE comparison would have called these
identical — the cheap fix, measured"* — that was green under every row
including a real size-comparing mutant, because both its assertions were about
two local constants and neither called the subject. That is the fifth shape in
`.claude/rules/checks-must-be-able-to-fail.md`: a case that certifies the
regression it was written to block.

Both of those were **measurements** — a number in a PR body, true of one tree
on one evening. AC-6's wording is *"each mutant built from the real source and
aborting loudly if its anchor moves"*, which describes a standing harness, so
this phase builds one: `test/preserve-overlap-battery.test.ts` constructs each
mutant by text substitution over the real source, refuses to run a row whose
anchor is not at exactly one site, loads the result as a module, and pins both
the original's and the mutant's answer to one named distinguishing input.

Three assertions per row rather than one, each closing a way the rule above is
satisfied on paper:

- **the anchor is in the real source exactly once** — a builder that silently
  finds nothing produces a row of zeros indistinguishable from a row of
  findings, and a builder that finds two sites changes something the row does
  not name.
- **the ORIGINAL's answer, pinned by value** — without it, *"they differ"* is
  satisfied by two wrong answers.
- **the MUTANT's answer, pinned by value** — `not.toBe` alone stays green when
  the mutant throws on the way to an empty answer, and a crashing mutant is
  not a mutant.

### The cheapest wrong fix, named once and answered

**Compare the file SIZE instead of the content digest** — `git cat-file -s`
in place of `git rev-parse <sha>:<path>`. It is the 5pm repair for *"tell me
whether these two copies are the same"*: one argument different, no new
concept, and right about almost every real input. It fails in the direction
that discards work, reporting IDENTICAL over two files that differ at the same
length.

**The shipped cases do not survive it, and the survival of the ones that do is
accounted for rather than left as a count.** Applied to the real source and
measured below as D2: **10 red of 48**, four of them in #892's own cases
(*coverage is reported even when the verdict is reached*, *the two blobs are
not equal*, *a SIZE comparison would have called these identical*, *the verdict
and its coverage are both on the line*) and six in the new harness.

The thirty-eight green are not all protection, and saying so is the point of
recording this:

- **Real survivals.** AC-1's *two worktrees agreeing about a path*, AC-3, AC-4
  and the whole of AC-6 take inputs a size comparison answers correctly —
  identical files are the same size, and a path with fewer than two readable
  blobs has no comparison to get wrong. They are green because the mutant is
  right about their input, which is a fact about the input and not a gap.
- **Vacuous survivals, named.** Before #991, *a SIZE comparison would have
  called these identical — the cheap fix, measured* was two assertions over
  two string constants, so it was green under a mutation of the subject it is
  named for. It now takes both readings over the same two commits and asserts
  they disagree, and it is one of D2's ten. Left unstated, a case with that
  title reads as coverage; this is the entry that stops it.

**Provenance, stated rather than implied.** The pre-fix record required by
#892's AC-7 is the docblock of `test/preserve-overlap-reading.test.ts`, written
before #950's fix and naming both cheap fixes (the size comparison, and `new
Set(blobs).size <= 1`). This section is a Phase 2 reading of that record, not
a re-authoring of it: the statement above is dated here and cites the earlier
position, because a statement whose value is that it preceded the fix cannot be
created afterwards in a document that implies it did not.

### The refusal-kind registry is TOTAL over a closed union

`test/claim-refusal-kinds.test.ts` holds eight kinds — not six, as two earlier
readings of this work recorded. The table that drives them was an array with
`kind: string`, looked up by `KINDS.find(r => r.kind === "co-owned conflict")!`,
and the remedy table beside it was `Record<string, string[]>` holding two of
the eight. A `Record<string, …>` has no opinion about a key it lacks, so the
two kinds added after it (#400, #629) simply had no remedy asserted and nothing
said so — `UNCLASSIFIED` arriving at the end of a run instead of at the top of
a build.

Both tables are now total `Record`s over a `RefusalKind` union, and the
hand-picked pair of remedy cases is replaced by a loop over every kind. Each
kind declares either the phrases that make its refusal actionable or an
explicit reason it carries none; a blank opt-out is refused, because an escape
hatch with no reason is one somebody takes by reflex.

**The two readings are deliberately different instruments, and each has an
input only it can reach** — not two deciders for one question:

- a kind added to the union with no row in either table is **a typecheck
  error** and the suite stays green (R2 below: 36 pass, 0 fail, 2 errors).
- a refusal template added to `workflows/ship.js` with no kind at all is
  invisible to the type system and is caught by *the table covers every
  refusal the block can emit*, which counts templates in the source (R1).

- [x] SC-2460: test/preserve-overlap-battery.test.ts contains [the anchor is in the real source exactly once]
- [x] SC-2461: test/preserve-overlap-battery.test.ts contains [the MUTANT answers it differently, and the difference is the named one]
- [x] SC-2462: test/preserve-overlap-battery.test.ts contains [a mutant is a different module, not the subject under another name]
- [x] SC-2463: test/claim-refusal-kinds.test.ts contains [every kind that declares a remedy carries it in the real message]
- [x] SC-2464: test/claim-refusal-kinds.test.ts contains [a kind that declares no remedy is not quietly carrying another kind's]

### What was broken to prove it (SC-2460..2464)

Every count was predicted before the battery ran — written to
`/tmp/906-battery/predictions.md` first — and **the baseline row was read
before any mutation row**, because an instrument that has stopped reporting
takes the baseline down with it and that is the row nobody mutates anything to
produce. Measured on `a7a42604` plus this branch's changes.

**Baseline: `test/preserve-overlap-reading.test.ts` + `test/preserve-overlap-battery.test.ts` — 48 pass, 0 fail.**

| Row | Predicted | Red | The input on which mutant and original differ |
|---|---|---|---|
| **D1** the naive `new Set(blobs).size <= 1` applied to the real source | 11 | **11 of 48** | `only-alpha.ts` over `[alpha, beta]` — one readable blob: original `UNMEASURED`, mutant `IDENTICAL` |
| **D2** THE CHEAPEST WRONG FIX — `git cat-file -s` for `git rev-parse <sha>:<path>` | 10 | **10 of 48** | `edited.ts` over `[alpha, beta]` — 24 bytes in both commits, one character apart: original `DIFFERS`, mutant `IDENTICAL` |
| **D3** coverage stops travelling with the verdict — `read: readings.length` | 14 | **14 of 48** | `edited.ts` over `[alpha, beta, gamma]` — gamma does not have it: original `read 2/3`, mutant `read 3/3` |

All three matched prediction, and matched it *by assertion* and not only by
count — which is the check a total that happens to agree does not pass:

- **D1's 11** are #892's five UNMEASURED cases (AC-3 *a path only one worktree
  has*, AC-4 *a path no worktree has*, AC-4 *no usable entries at all*, AC-5
  *an unreadable position prints its reason*, AC-6 *a failed preserve entry
  contributes no reading*) and six in the harness: all three of M2's
  assertions, M3's anchor and mutant assertions — M2's anchor **contains**
  M3's, so applying M2 to the source removes M3's site and the builder aborts
  loudly rather than measuring a no-op — and M6's verdict control.
- **D2's 10** are the four named under *the cheapest wrong fix* above, plus all
  three of M4's assertions, M3's original-answer assertion, and both of M5's.
- **D3's 14** are #892's five coverage cases plus nine in the harness,
  including the two fixture preconditions (*M2's input really has exactly one
  readable blob*, *M5's input really is readable in two of three positions*)
  and the builder control *a mutant is a different module* — whose anchor is
  the very line D3 mutates, so it aborts.

**Baseline: `test/claim-refusal-kinds.test.ts` — 36 pass, 0 fail; `bun run typecheck` — 0 errors.**

| Row | Predicted | Measured | The input on which mutant and original differ |
|---|---|---|---|
| **R1** a kind deleted from the union and from both tables | suite 1, typecheck 0 | **1 of 35, typecheck 0** | the source itself: eight `${wt} reported ` templates against seven rows |
| **R2** a ninth kind added to the UNION only | suite 0, typecheck 2 | **0 of 36, typecheck 2 errors** | the declaration: `Record<RefusalKind, …>` is missing a property, and bun strips types so nothing executes differently |
| **R3** the remedy table reverted to `Record<string, Remedy>` with one entry deleted | suite 3, typecheck 0 | **3 of 35, typecheck 0** | `REMEDY["multiple claimants"]` — a `Remedy` under the union, `undefined` under `string` |

**R2 is the row that matters and its suite column is zero on purpose.** It is
the pre-#906 failure reproduced: a kind exists, nothing classifies it, and the
suite is green. The instrument that catches it is the typechecker, so a green
suite is not evidence here — which is why the row is recorded with two columns
rather than one.

**R3 says the runtime loop is not redundant with the type, and does not say
the type is redundant with the loop.** The loop catches a missing entry only
when something reads it at runtime; R2 is an entry missing with the suite
green, which is the input only the type reaches. That is
`.claude/rules/checks-must-be-able-to-fail.md`'s second option for two
deciders — keep both, and give each an input only it can reach — rather than
the collapsed pair the same section warns about.

No mutation is left in the tree. `scripts/preserve-worktree-work.ts` and
`test/claim-refusal-kinds.test.ts` were each copied with `cp` before the first
row, restored from that copy after every row, and confirmed **byte-identical by
`shasum -a 256 -c`** rather than by `git checkout --`.

### What this does NOT do, stated rather than left as an omission

- **AC-8's two named rows cannot be added.** `content-differs` and
  `unreadable-comparison` appear nowhere in `lib`, `scripts`, `workflows` or
  `test`. #950 shipped option C — the reading composes the operator-facing
  message and changes no decision — so there are no new refusal templates for
  those rows to describe. Inventing registry entries for templates nothing
  emits is #979's defect class in the registry whose job is to prevent it. The
  totality above is what AC-8's property reduces to against the tree that
  exists.
- **The four `ship.js` source-text cases in `test/preserve-overlap-reading.test.ts`
  still have no demonstrated failing input** beyond *the schema DECLARES
  overlapLines*. They assert over a file this harness cannot mutate as a
  module, and they are reported as uncovered rather than counted as cases.

## #1038 — work that exists on this machine and nowhere else

A worktree is removed at the end of an ordinary session while its branch stays
in `.git` holding the commits, so a reading attached to `git worktree list`
cannot see most of the population it exists to find. Measured on this machine
2026-10-31: **14 branches held 25 commits reachable from no `origin/*` ref, and
5 of them still had a worktree.** Nine of fourteen were invisible to every
instrument in the repository.

Nothing reported it, for three reasons that had to hold at once. The rule in
`.claude/rules/parallel-sessions.md` — *"Push finished work"* — has nothing
executing it. `unpushedKeepReason` in `lib/worktree-cleanup.ts` asks the right
question but only of worktrees, and only to decide whether to *keep* one. And
`git status --porcelain`, which is how both the census and
`CommitEnforcement.hook.ts` decide a tree is "clean", returns zero lines for a
committed-but-unpushed branch — so **committing is the step that makes work
invisible.** An agent that leaves a mess is flagged; an agent that tidily
commits and stops is silent.

The remedy is a push rather than a report, because a push ends the condition
instead of describing it, and is idempotent — a branch already on origin costs
one no-op round trip. The default branch is excluded: pushing it is either a
no-op or an attempt to move a protected ref, and neither belongs in a hook that
runs unattended at every session start.

### Why `examined` is a field and not a length

`pushed: []` with `examined: 0` is an instrument that did not run.
`pushed: []` with `examined: 14` is a clean tree. A bare count of rescues
spells those the same way, which is how "zero violations" comes to mean
"nobody looked" — the shape named in
`.claude/rules/checks-must-be-able-to-fail.md` as an assertion that holds
vacuously. `unmeasured` carries the third case, a reading that could not be
taken at all.

### What was broken to prove it (SC-2630..2631)

Four mutations of `lib/worktree-cleanup.ts`, each run against
`test/worktree-cleanup.test.ts`, baseline 13 pass / 0 fail:

| Mutation | Result |
|---|---|
| finder drops the `n > 0` filter, reporting every branch | 2 fail |
| rescue reports success without invoking `git push` | 1 fail |
| the default branch is no longer excluded | 1 fail |
| a failed reading returns `unmeasured: null` | 1 fail |

The second is the one that matters: it asserts by asking git again after the
rescue, not by reading the return value, so a rescue that reports success
while pushing nothing goes red.

- [ ] SC-2630: lib/worktree-cleanup.ts contains [export function strandedBranches] — every local branch holding commits reachable from no origin ref, asked of branches rather than worktrees, with a repo that has no origin returning an empty list rather than every branch
- [ ] SC-2631: lib/worktree-cleanup.ts contains [export function rescueStrandedBranches] — the branches are pushed rather than reported, never with --force and never the default branch, and the result separates a clean tree from a reading that could not be taken

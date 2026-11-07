---
doc-type: spec
testable: true
compliance: strict
evidence: required
governs: Automated code review convergence — the mechanisms from Anthropic's "Solving code review" that RunGate adopts, what each one must do, and how we know whether it works. This is the alignment reference for all finding-arbiter, jury, review-depth and approval work.
status: active
owner: jason
created: 2026-10-22
source: https://claude.dev/blog/solving-code-review-at-anthropic/
updated: 2026-11-07
---

# Code Review Convergence

## Why this document exists

The finding-arbiter work was dispatched from a blog post and then run from memory.
There was no written reference, so there was nothing to drift *from* and nothing that
could say we had. Two symptoms, both measured on 2026-10-22:

- **Two PRs (#1280, #1282) implemented #1261 simultaneously**, in different files, to
  different ideas of "done". Neither was wrong; nothing defined the target.
- A mechanism nobody asked for (a PR-collision check) was added to the arbiter's scope
  by the lead mid-flight. It may well be a good idea. It is not in the source.

This spec is the target. **Anything not in here is drift until it is added here.**

## The reframe this is all downstream of

> Code review does two jobs: find issues before they ship, and build shared context.
> "Did a human read the code?" is **an imprecise proxy** for "what could go wrong with
> this change, and which check — automated or human — is the right one to catch it?"

Objective, stated in the source and adopted verbatim as ours:

> **The minimum amount of human review time that doesn't raise reverts or incidents.**

And the cost rule that stops us gaming it:

> Human time covers both sides of review's cost: the time people spend reviewing, and
> the time they spend fixing what bad code breaks. Cutting the first doesn't help if the
> time just shows up in the second.

## THE FINDING WE HAVE MOST VIOLATED

> **Every finding has to be answered. You either fix it or resolve the thread with a
> reason.**

Anthropic has no review backlog **because findings never become backlog**. A finding is
an inline comment that blocks merge until it is dispositioned. There is no filing step.

**We invented the filing step, and it is the systematic defect.** Measured on this repo:
359 issues filed *and* closed in seven days, median lifetime 3.1 hours, open flat at ~30.
That is a dispatch queue wearing a tracker's clothes. 45% of filings that name a file were
made while a PR was already open touching that exact file.

Every criterion below is subordinate to this one. A mechanism that makes filing smarter
without making *not filing* the default has missed the point.

## How we open a new area of this spec

**Standing practice, agreed 2026-10-28.** This spec holds 61 criteria. Picking one off
the list and building it is how the work has gone so far, and it is why three of the
figures in this document describe no system that exists. Criteria are not a queue.

Before any area of this spec is opened, the frame below is written **here**, not in a
conversation:

1. **Why** — the problem in one paragraph, in the language of what it costs.
2. **Target outcomes** — each with the measured baseline beside it **and the command
   that produced it**. An outcome whose baseline is untrustworthy gets no target until
   one has been measured; inventing a target against a number nobody believes is how
   this document acquired its bad figures. An outcome with no baseline at all makes the
   increment *"instrument it"*, never *"improve it"*.
3. **Competing hypotheses** — more than one, because the point of measuring is to
   choose between them.
4. **An increment** — the smallest set of criteria that together move one outcome.
   Several criteria, not one: a criterion that moves nothing on its own is not shippable
   on its own. This is a **Minimum Marketable Feature** (Denne & Cleland-Huang, 2003)
   — **UNVERIFIED, not read against the source; see the citation table below** — not an
   MVP: an MVP buys learning, an MMF delivers value.
5. **An appetite, and a circuit breaker.** A budget fixed before design. An increment
   that exceeds it is **cancelled by default** rather than extended by default; an
   extension has to be argued for. That is Shape Up's circuit breaker and it is
   **VERIFIED 2026-10-28** against the book itself: *"If they don't finish, by default
   the project doesn't get an extension"*, and its glossary gives the mechanism as
   *"Cancel projects that don't ship in one cycle by default instead of extending them
   by default"*. MMF says what to ship and is silent on what happens when it does not
   finish, which is the gap this closes.
6. **Exit criteria** — what must be true for the increment to be done, written before
   it starts.
7. **Pre-specified decision criteria** — which hypothesis each possible reading selects,
   **committed in advance**, including the reading that abandons the increment. Written
   after the measurement, it is a rationalisation. The test it must pass is
   determinism: *two people following the rule are guaranteed to reach the same
   decision*. A rule that needs interpretation is not one.
8. **A deviations record, written after the measurement.** Restate the decision criteria
   verbatim and list every departure from them. **This step, not step 7, is the one with
   evidence behind it** — see below.

A criterion that is plain correctness work with no outcome to move is marked
**"correctness only — no outcome claimed"** and skips steps 2, 3 and 7. Forcing an
outcome onto such a criterion manufactures a vanity baseline, which is worse than
declaring there is none.

### Why step 8 is not optional

Committing a decision rule in advance sounds sufficient and is not. The best available
comparison is van den Akker et al., *Preregistration in practice*, **Behavior Research
Methods** (2023), `doi:10.3758/s13428-023-02277-0`. **Read 2026-10-28 from the
publisher's PDF**, the abstract states it compared *"193 psychology studies that earned
a Preregistration Challenge prize or preregistration badge to 193 related studies that
were not preregistered"* and that *"we did not find that preregistered studies had a
lower proportion of positive results (Hypothesis 1), smaller effect sizes (Hypothesis
2), or fewer statistical errors (Hypothesis 3)"*.

So the artefact that does the work is the deviations record, not the rule. A
pre-specified rule with nothing comparing it to the outcome is decoration.

**Two figures previously in this paragraph are WITHDRAWN** — *"roughly three quarters
of preregistered studies deviate from their plan"* and *"adherence rises to about 92%"*.
Both were credited to the paper above and **neither is in it**; its design compares
preregistered to non-preregistered studies and does not measure deviation from a plan
at all, so the attribution was structurally wrong and not merely unlocated. Deviation
rates are a different literature with different numbers, and this document is not
standing on figures it has not read. The claim above survives on the headline result
alone, which is weaker and checked.

### Every external citation in this section, and whether anybody read it

Round 11 of #1637 observed that the external claims here rest on the same mechanism that
produced the withdrawn Mobius attribution, and that nothing in this repository can check
any of them. Round 12 then made the sharper point: a sentence *saying* the others are
unverified, three paragraphs away from where they are asserted, is not a mark on any of
them — a reader scanning the claims sees confident prose. Both are correct, and the
round-11 census was **itself short by one**: it named five claims and missed Pre-SPEC
entirely. A census of unchecked claims that is not itself complete reproduces the defect
it records, so the population is enumerated here rather than counted.

Each row is marked at its own claim site as well as in this table.

| Citation | Status | What was actually read |
|---|---|---|
| van den Akker et al., *Preregistration in practice*, 2023 | **VERIFIED** 2026-10-28 | Publisher PDF; abstract quoted above. Cost two withdrawals. |
| Shape Up, the circuit breaker | **VERIFIED** 2026-10-28 | `https://basecamp.com/shapeup/2.2-chapter-08` and the glossary; both quoted above. |
| Pre-SPEC (Kahan, Forbes & Cro, 2020) | **VERIFIED** 2026-10-28 | Open-access full text; points 4 and 5 and the determinism definition quoted above. |
| Open Practice Library / Mobius | **WITHDRAWN** | Practice page read; the *options pivot* URL returns HTTP 404. |
| MMF (Denne & Cleland-Huang, 2003) | **UNVERIFIED** | Nothing. It is a book and no copy was consulted. |
| GQM (Basili et al., NASA SEL) | **UNVERIFIED** | A search returned only a secondary method guide; no primary text. |
| ISO/IEC/IEEE 15939:2017 | **UNVERIFIED** | Nothing — paywalled; ISO's browsing platform returned HTTP 403. |

Three read, three not, one withdrawn. The three unread are the three that are hardest to
reach, which is the honest reason and not a good one; what this table buys is that no
reader has to guess which is which.

### Provenance, and one correction

The first draft of this section called the above "one turn of a Mobius loop". That
attribution was **wrong and is withdrawn**. Checked directly: the Open Practice Library's
*Target Outcomes* practice prescribes a whiteboard template, a visible timer, Start At
The End, Affinity Mapping and a SMART goal — **no baseline step, no current-state
measurement, no instrumentation**. And the Open Practice Library URL for "options
pivot" — `https://openpracticelibrary.com/practice/options-pivot/` — returns
**HTTP 404**; it is a phase label, not a practice, and carries no
decision rule. The two things this section most needed are precisely the two Mobius does
not supply; they were invented here and credited to it.

The honest lineage is older and testable. **GQM** (Basili et al., NASA SEL) writes its
*interpretation model* alongside the questions, before any data — **UNVERIFIED: no
primary Basili or SEL text was read; a search on 2026-10-28 returned only a secondary
method guide.** **ISO/IEC/IEEE 15939:2017** makes *decision criteria* a defined term —
thresholds fixed in advance that determine the need for action — and defines an analysis
model as measures combined with them: **UNVERIFIED, and not cheaply verifiable — the
standard is paywalled and ISO's browsing platform returned HTTP 403 on 2026-10-28.** The
determinism test in step 7 is **Pre-SPEC** (Kahan, Forbes & Cro, *BMC Medicine* 18:253,
2020, `doi:10.1186/s12916-020-01706-7`), and this one is **VERIFIED 2026-10-28** from the
open-access full text: its fifth point is *"adaptive analysis strategies should use
deterministic decision rules"*, and it defines the test as *"A decision rule is
deterministic if two different people are guaranteed to get the exact same result by
following the rule"* — which is step 7's sentence, and the paraphrase was faithful.
Mobius is prior art here and nothing is inherited from it.

## The current loop — Increment 1: make the verdict readable

**Why.** A change costs about four and a half review rounds, and 45.8% of rounds end
with no readable verdict. The second number is the worse one: a round that could not be
measured is indistinguishable from a round that found nothing, so the gate's silence
carries no information. That is SUCCESS.md claim 4 failing inside this repository's own
merge gate.

**Target outcomes.**

Every baseline carries the day it was taken and the command that produced it.
Step 2 of *How we open a new area of this spec* requires both, and an earlier
revision of this table carried neither — caught by the required reviewer on
2026-10-28, which is the document failing its own rule inside the section that
states it.

| # | Outcome | Baseline | Taken | Command | Target |
|---|---|---|---|---|---|
| O1 | Rounds to pass | 4.50 — **untrustworthy** | 2026-10-28 | `bun evals/ai-review-control/run.ts rounds` | set at the end of this loop |
| O2 | One-round pass rate | 26.1% — **untrustworthy** | 2026-10-28 | `bun evals/ai-review-control/run.ts rounds` | set at the end of this loop |
| O3 | Rounds ending unreadable | 45.8% | 2026-10-28 | `bun evals/ai-review-control/run.ts rounds` | ≤5% |
| O4 | A reading describing ONE configuration | does not exist (n=1) | 2026-10-28 | the same reading, partitioned by configuration — no command produces it today, which is what O4 says | n≥12, configuration named |

All three numeric baselines come from one reading over **#1573–#1634: 48 pull
requests, 203 rounds**. The denominator for O2 and O3 is **rounds**, not pull
requests. O4's cell has no command on purpose: the absence IS the baseline, and
inventing one would be the vanity baseline this frame warns about.

O1 and O2 carry no target **by decision**. Both were measured across #1573–#1634, which
spans at least two mechanism changes (#1614 made the advisory reviewer run on every pull
request; #1634 made repeat suppression live) and a third landed in #1636. A cohort that
spans a mechanism change describes no system, so a target set against it would be a
number invented to look like a plan. O4 is what makes O1 and O2 real, which is why it is
in this loop and they are not.

**Options — competing hypotheses.**

| | Hypothesis | What would select it |
|---|---|---|
| H1 | Most unreadable rounds are the reviewer never reading the code at all | unreadable rounds are mostly zero-tool-call |
| H2 | The reviewer stops early because `REVIEW.md` asks for its three best guesses; told to cover the change, it reports materially more per pass | unreadable rounds mostly DID call tools |
| H3 | Rounds are high because findings arrive in a drip, not because there are many | findings-per-round flat across rounds at constant diff size |
| H4 | Truncated diffs caused part of the miss rate | superseded — the cap moved in #1636; now measurable |

**The increment.** CRC-M12, CRC-M13, CRC-M14, CRC-M15 below, shipped as a set. Each is
one pull request; none of them moves O3 or O4 alone.

**Appetite and circuit breaker.** Four pull requests and one release. An increment that
has not produced a reading after that is **cancelled, not extended** — and its
cancellation is itself a result about O4, because it would mean a single-configuration
reading cannot be taken by this route.

**Exit criteria — all five, or the increment is not done.**

1. An unreadable round reports **which** named mode it was, not merely that it was unreadable.
2. The share of unreadable rounds with zero tool calls is a recorded number.
3. Every reading in the store names the published version it was taken under.
4. A cohort row exists describing a single configuration, with that configuration
   named, over **n≥12 rounds** — the same n the O4 target states. An earlier revision
   wrote this as "one cohort row exists", which is satisfied at n=1 and would have
   closed the increment on a reading too thin for the decision table below to read.
   Caught by the required reviewer on 2026-10-28.
5. O1 and O2 carry a target, **or** a written statement of why they still cannot. Their
   Target column promises one at the end of this loop and criteria 1–4 never ask for it,
   so without this row the promise is enforced by nothing. "Still untrustworthy, because
   X" is a complete answer; silence is not.

**Pre-specified decision criteria, committed before the measurement.** Each reading
below selects exactly one next increment, so two readers of the same number reach the
same decision.

**Rows are evaluated in order and the first match wins.** Without that sentence the
futility row overlaps all three percentage rows — any n<12 reading also lands in one of
them — and two readers could reach different decisions from one number, which is exactly
the determinism test this section claims to pass. Caught by the required reviewer on
2026-10-28, and it was right: a table whose rows are not disjoint is not a decision rule.

| Order | Reading on the unreadable rounds | Selects | Next increment |
|---|---|---|---|
| 1 | fewer than **12** unreadable rounds recorded in one configuration | neither — **futility** | the instrument did not produce enough draws; cancel and re-scope rather than read a number this thin. Evaluated FIRST, so a thin reading never reaches a percentage row |
| 2 | **> 60%** have zero tool calls | H1 | reviewer reliability — a prompt A/B would be measuring the wording of an instruction nothing read |
| 3 | **< 40%** have zero tool calls | H2 | the `REVIEW.md` A/B, testing the standing prediction (current ~1 finding/pass, coverage arm ≥2.5×) |
| 4 | **40–60%** inclusive of both endpoints | both | H1 first, because it is the cheaper build |

**H3 is not selectable by this reading, and that is a decision rather than an
oversight.** The table branches on one axis — whether the unreadable rounds called tools
— and H3 is a claim about findings-per-round at constant diff size, which this
increment's instruments do not measure. So no reading above can select it. H3 stays in
the Options table as live and **unaddressed**, and if rows 2–4 all turn out to be wrong
it is the first thing to instrument. Writing a fifth row for a hypothesis nothing here
can test would be a decision criterion no measurement could trigger, which is worse than
saying so.

**Deviations record — to be written after the measurement, and empty until then.**
Restate the table above verbatim and list every departure from it. If no reading was
taken, say that. An increment that closes with this section still empty has not closed.

**Increment 2 is not scoped here, deliberately.** Its content is whichever row of the
table above the measurement selects, and scoping it now would commit the choice before
the evidence.

## Housekeeping — carried here so it is visible, but it is not criteria

Three known items move none of this document's outcomes. They are written down because
work nobody can see gets rediscovered, and left out of the criteria list because
`CLAUDE.md` is right that cleanup should say it is cleanup rather than borrow urgency
from something that is measured. **Nothing below gates an increment.**

- [ ] Two rows are missing from `CENSUS_TRIGGERS` in `scripts/census-routing.ts`, so the
      router under-reports which census tests a diff can trip.
- [ ] The `Cited` table in this document is hand-maintained and should be rendered from
      data, like the routing table in `.claude/rules/self-referential-tests.md` already is.
- [ ] Three scare quotes are silently dropped in the generated `.github/workflows/ai-review.yml`.
      The advisory reviewer reported this as breaking the shell string early; **that claim
      was checked by running both lines and is false** — exit 0, no stderr, full sentence
      emitted. What remains is cosmetic.

## Success criteria

Criteria are grouped by the source's own layers. Each states the mechanism, not the
implementation.

### This document is bound to the evidence rule

Its frontmatter carries `evidence: required`, so `bun bin/rungate.ts audit-spec-evidence`
refuses it unless every criterion says what would prove it and every ticked criterion
says what did. The rule and the checker shipped in #1639; this is the first document
retrofitted onto them, and the second bound to them at all.

Every one of the 61 criteria carries a `needs:` line naming one of `test`,
`measurement`, `run` or `review` — what KIND of proof it will take, which is a statement
this document can make today about work nobody has started. Ticked criteria also carry
`proved-by:` naming what was run, and `fingerprint:` binding that evidence to the
criterion's exact wording, so **rewording a criterion invalidates what proved it**
rather than silently carrying the claim across.

**Two ticked criteria are waived rather than proved, and the waivers are the point.**

| Criterion | Why | Expires |
|---|---|---|
| CRC-B7 | #1567: nobody has run a finding through the live path and observed a demotion, so the tagging is not verified end to end. | 2026-12-31 |
| CRC-M11 | #1592: the metric counts run ATTEMPTS and the sentence says ROUNDS, so what is tracked is not what is claimed. | 2026-12-31 |

**Both are signed `rayford`, which is an agent, and neither is countersigned.** The
first draft of this section wrote `waived-by: jason`, and he did not sign them — an
agent did, while he was away. A waiver is an escape hatch whose only safeguard is that
somebody's name is on it, so signing it with the name of a person who never saw it
removes the safeguard while leaving every field populated. That is the BMW lobster
defect in its worst form: not an empty justification, a false one. Countersigning is a
one-line edit and the expiry is the prompt to make it.

Both keep their `needs:` line. A waiver replaces `proved-by:`, never `needs:` — it
carries an expiry, so what it will take to prove is exactly what you want recorded while
deciding not to take it yet. Both were found by a sweep of every ticked criterion in
the tree against every open issue, matching ids on word boundaries; no figure is quoted
for it here because that reading has no recorded command, and this document does not
stand on numbers nobody can re-take. Both were ticked by a mechanism that reads a
comment in a test file, which is the defect the evidence rule exists to replace.

**It was red before it was green, on this document.** The first audit after annotation
raised eight `FINGERPRINT_MISSING` violations, one per ticked-and-proved criterion, and
exited non-zero. After recording, rewording a single word of CRC-C4 — *"if"* to
*"when"* — turned it red again with `EVIDENCE_STALE`, naming both hashes. That is the
check proving it can fail against this file and not against a fixture.

### Layer 1 — before the PR

- [ ] CRC-A1: The agent is given something runnable and must show the output, not assert completion.
      needs: run
- [ ] CRC-A2: A fresh-context subagent reviews the diff before the PR opens.
      needs: run
- [x] CRC-A3: `CLAUDE.md` is short, states stack/conventions/goals/non-goals, and points elsewhere for detail.
      needs: test
- [x] CRC-A4: The reviewer flags code breaking a `CLAUDE.md` convention, AND changes that make a line in it out of date.
      needs: test
- [x] CRC-A5: `REVIEW.md` exists per owned area, written by code owners. (shipped, #1167)
      needs: test
      proved-by: test/ai-review-conventions.test.ts (AC-C10) — 371 pass, 0 fail, 2026-10-28
      fingerprint: ec46dbf8
- [x] CRC-A6: A check reports whether the reviewer actually followed `REVIEW.md`. (shipped, #1233/#1246)
      needs: test
      proved-by: test/ai-review-conventions.test.ts (AC-C1..AC-C9b) — 371 pass, 0 fail, 2026-10-28
      fingerprint: ebeaeab9
- [ ] CRC-A7: `REVIEW.md` caps the nits, lists paths to skip, demands file-and-line evidence rather than a guess from a name, and requires a summary that starts with a count and says plainly when there is nothing to fix.
      needs: test
- [ ] CRC-A8: **Fix at the source.** When the reviewer keeps flagging the same thing, the repair goes into the skill, a lint rule, or an instruction file — not into another finding.
      needs: test

### Layer 2 — AI review on every PR

- [x] CRC-B1: The reviewer reads the diff against the whole repo **and the PR's stated intent**.
      needs: test
- [ ] CRC-B2: On a bug fix, the reviewer looks for the root cause.
      needs: test
- [ ] CRC-B3: **Several agents look for bugs at the same time** (parallel generation). **Not an unqualified good here, and the qualification is CRC-B4's, pointed the other way.** The reviewer is a *sampled* instrument, so N generators are N draws and they raise recall and the false-positive rate together. Measured on run `39962683401`: two attempts on merge commit `99d50fc`, both at round 5, with the tree, the head, the prompt and the model all held fixed, returned **BLOCKED then CLEAN** — and the blocking finding was false, claiming a routing row that was present at the reviewed head. So the disagreement a second draw buys has already been observed arriving in the costly direction. Under the source's priority that trade is worth taking; under ours it is not, because CRC-M8 is inverted here by declared decision and a false block costs a remedy commit, a CI round, a review round and an agent's whole context. **Parallel generation without CRC-B4's quorum behind it is therefore strictly worse than one generator** — it is N chances to block on a false positive with nothing filtering them — so this criterion is not adoptable before CRC-B4, and adopting it first would be measurable harm rather than partial progress.
      needs: measurement
- [x] CRC-B4: **A separate group of agents votes on each finding**, and it is surfaced only if enough agree it is real. The ledger records **every verifier's individual vote** and **whether the verifiers disagreed**, both as first-class fields written at decision time. Without them every threshold except the one actually used is permanently UNMEASURED, and re-running to recover the votes re-samples the thing being measured. **A reading the mechanism produces whether or not it works does not satisfy this criterion.** Measured: the deployed filing path takes no votes at all — a regex over the title and set arithmetic over symptom keys, with no clock, model or network — so a variance control over it reports a single distinct outcome set, zero variance, by construction, and the reading that looks most like success is the signature of the failure mode. **Nor does a reading that varies for a reason other than the mechanism under test** — name the mechanism the reading is of, not only the number it produced. Where the flattering reading is available by construction, the criterion names what would distinguish it from the real thing, or declares itself UNMEASURED.
      needs: test
- [x] CRC-B5: Findings that are only **style, diagnostics or cleanup** are dropped.
      needs: test
      proved-by: test/issue-filing-gate.test.ts (WIRING + the DROPPED_CATEGORY rows) — 371 pass, 0 fail, 2026-10-28
      fingerprint: 44bbb6ba
- [ ] CRC-B6: The filters are **A/B tested** against real PRs before being kept, **with variance bounded**. The reviewer is a sampled instrument, so two verdicts on the same code are two draws; an A/B that does not account for that is comparing noise.
      needs: measurement
- [x] CRC-B7: Surviving findings are **sorted by severity** and tagged **Important / Nit / Pre-existing**, so a pre-existing bug does not read as the author's fault. (shipped, #1587)
      needs: test
      waived-reason: #1567 records that nobody has run a finding through the live path and observed a demotion, so the tagging is NOT verified end to end
      waived-by: rayford (agent; not countersigned by jason)
      waived-until: 2026-12-31
- [x] CRC-B8: **Every finding is answered** — fixed, or resolved with a stated reason. A finding is never silently dropped and never becomes a tracker item by default.
      needs: test
- [ ] CRC-B9: Review depth is configurable per repo as **Quick / Standard / Deep**.
      needs: test

### Layer 3 — security review

- [ ] CRC-C1: Security review is a separate automated pass.
      needs: test
- [x] CRC-C2: A PR cannot merge while any bug-review or security-review finding is open.
      needs: test
- [x] CRC-C3: A false positive clears by closing the thread with a short reason.
      needs: test
- [x] CRC-C4: A finding clears on its own if a later commit fixes it.
      needs: test
      proved-by: test/ai-review-workflow.test.ts (AC-3b) — 371 pass, 0 fail, 2026-10-28
      fingerprint: c4bf24ad

### Layer 5 — human approval scaled by risk

- [x] CRC-E1: Risk tiers are written down: low needs no human, medium one, high two. (shipped, #1437)
      needs: test
      proved-by: test/risk-tier.test.ts "CRC-E1: the tiers are written down — low none, medium one, high two" — 371 pass, 0 fail, 2026-10-28
      fingerprint: a0fed192
- [x] CRC-E2: **The change sets the tier, not the author** — a classifier reads the change. (shipped, #1437)
      needs: test
      proved-by: test/risk-tier.test.ts "CRC-E2: the CHANGE sets the tier, not the author" — 371 pass, 0 fail, 2026-10-28
      fingerprint: 5de29c3d
- [ ] CRC-E3: A **second classifier** asks whether this change needs another person even when its tier says no.
      needs: test
- [x] CRC-E4: Owner-listed sensitive paths and **any CI workflow file** always require a human. (shipped, #1437)
      needs: test
      proved-by: test/risk-tier.test.ts "CRC-E4: any CI workflow file, and any owner path, always needs a human" — 371 pass, 0 fail, 2026-10-28
      fingerprint: e0c4546a
- [ ] CRC-E5: Only trusted authors get the lighter paths.
      needs: test
- [ ] CRC-E6: **An agent's approval never counts as a person's.**
      needs: test
- [x] CRC-E7: Whoever prompted the change counts as one of the required reviewers.
      needs: test
- [ ] CRC-E8: **An approval covers one specific commit**; new commits the system cannot vouch for dismiss it.
      needs: test
- [ ] CRC-E9: Tiers **start strict and loosen with evidence**.
      needs: measurement

### Layer 6/7 — merge, release, detection

- [ ] CRC-F1: A merge queue re-runs every check against main with the change applied.
      needs: test
- [ ] CRC-F2: New behaviour ships behind a flag, internal users first.
      needs: test
- [ ] CRC-F3: One-step rollback exists and is exercised.
      needs: test
- [ ] CRC-F4: Incident reviews ask **which layer should have caught it**.
      needs: review
- [ ] CRC-F5: Circuit breakers tighten approval when revert/incident rates move. *(the source names this as an admitted gap on their side; we adopt it as a target, not a copy)*
      needs: measurement

### Measurement — how we know any of this works

- [x] CRC-M1: **Incidents are an eval.** Past incident-causing PRs, with fix-forwards and reverts, form a case set.
      needs: review
- [ ] CRC-M2: Each case is **expert-confirmed** — a human who knows the code confirms the bug and where it lived.
      needs: review
- [ ] CRC-M3: **Every new incident adds a case.**
      needs: review
- [ ] CRC-M4: Any change to the reviewer's prompts, tools or model is **rescored against the whole set**.
      needs: test
- [ ] CRC-M5: The eval runs **daily**; a change that raises the score is kept, one that does not is dropped.
      needs: run
- [ ] CRC-M6: **Noise is measured by what people do with the comments**, in four buckets: fixed it / said it was wrong / said it was intentional / decided it didn't matter.
      needs: measurement
- [ ] CRC-M7: A **clean-PR control** counts how often the reviewer reports something that would have led to a harmful change. (exists, `evals/ai-review-control/`)
      needs: measurement
- [ ] CRC-M8: Priority order is stated and enforced: **catching real bugs first, cutting review rounds second.**
      needs: measurement
- [ ] CRC-M9: Human-time metrics tracked — approvals per PR (median and p95), human comments, time waiting on a person.
      needs: measurement
- [ ] CRC-M10: **Revert and incident rates are the guardrail.** If they rise, human time was moved, not saved.
      needs: measurement
- [x] CRC-M11: Rounds-to-pass is tracked alongside recall. (shipped, #1441/#1448)
      needs: measurement
      waived-reason: #1592 records that the metric counts run ATTEMPTS while this sentence says ROUNDS, so what is tracked is not what is claimed
      waived-by: rayford (agent; not countersigned by jason)
      waived-until: 2026-12-31

Increment 1 of *The current loop* above. These four are a set: each one alone leaves the
unreadable rate exactly where it is.

- [ ] CRC-M12: **An unreadable round names its mode.** `no_payload` (the action ran and
      wrote no findings file), `none_posted` (findings were written and none reached the
      pull request) and `diff_truncated` (the reviewer was shown part of the change) are
      **distinct recorded outcomes**, not one bucket. A round recorded as merely
      "unmeasured" is the defect this criterion exists to remove: it is the state that
      reads as "nothing wrong" to every consumer of the number.
      needs: test
- [ ] CRC-M13: **Whether the reviewer READ anything is recorded, separately from whether
      it WROTE anything.** `lib/review-execution-reading.ts` already computes
      `toolCallsByName` and `NO_TOOL_CALLS`; it is wired into the advisory reviewer only,
      and the required reviewer runs in consumer repositories that have no `scripts/`
      directory, so the reading is unreachable there. The criterion is met when the
      required reviewer reports the tool-call census on the no-payload route — **not**
      when the library can compute it. A reading nothing invokes is not a reading.
      Satisfying this needs the reader published as a CLI command, hence a release.
      needs: test
- [ ] CRC-M14: **Every reading names the published version it was taken under.** CI pins
      `bunx rungate@<version>`, so a merged change to `lib/` is dormant until a release
      while a merged workflow change is live immediately. A reading that does not say
      which published version produced it cannot be attributed to a configuration, and
      an unattributable reading is what O1 and O2 above are made of.
      needs: test
- [x] CRC-M15: **The staleness check reads contents, not a version string.**
      `lib/distribution-standing.ts` makes **two** comparisons on **two different
      fields**, and neither reads an artefact. `standing.published` — the version a
      consumer can install — is checked for membership in
      `[registry.latest, registry.previous]`, so one release of lag is permitted
      unconditionally. `standing.tree` — the version the measurements were taken
      against — is checked for equality with `package.json`'s version, and never
      against the registry at all. **It never reads the published artefact** — two
      earlier drafts of this criterion got this wrong in two different ways: the
      first said it compared package SIZE, the second said the measurement-baseline
      field was the one compared to the registry. Both were corrected on 2026-10-28
      after the required reviewer read the module, in rounds 5 and 6. The gap is not
      the comparison it makes but the one it does not:
      a version match says nothing about whether the published tarball carries a `lib/`
      fix that is already merged, which is exactly how a merged change stays dormant
      behind a green check. Met when a package whose version is acceptable and whose
      contents differ from the tree is refused, by name.
      needs: test

### Convergence — the non-convergent review failure

The source's measured failure: one PR ran **more than fifty rounds overnight**; git blame
showed **~59%** of what the reviewer kept flagging was code present at its first pass.

- [x] CRC-N1: **A round cap.** After three rounds the reviewer asks the author to step back and reconsider the approach. (shipped, #1168)
      needs: test
      proved-by: test/ai-review-rounds-step.test.ts (AC-S1..AC-S5) — 371 pass, 0 fail, 2026-10-28
      fingerprint: 72c24240
- [x] CRC-N2: **Diff-only re-review** after the first few passes.
      needs: test
- [x] CRC-N3: **Flag the class of bug**, so the author fixes every instance rather than one line.
      needs: test
- [x] CRC-N4: **No repeats** of findings already posted.
      needs: test
- [ ] CRC-N5: Review agents run **nightly over existing code**.
      needs: run
- [ ] CRC-N6: **A fixed defect stays fixed.** A finding must not be re-raised from text that merely DESCRIBES it — a docblock quoting the code that was removed, or prose narrating what the bug used to be.
      needs: test

Their result, which is our target: pass-after-one-round 65% → 78%; five-or-more rounds
8.9% → 1.5%; mean reviews to pass 2.08 → 1.32.

### Where we actually stand, measured

The first reading CRC-M11 was able to take, over the 45 most recent pull
requests on 2026-10-23 — 44 measured, 1 refused for carrying no ledger:

| | their before | their after | **us** |
|---|---|---|---|
| passed after one round | 65% | 78% | **39.4%** |
| five or more rounds | 8.9% | 1.5% | **20.5%** |
| mean rounds to pass | 2.08 | 1.32 | **2.64** |

**We are worse than the state they were improving from, on all three.** That
is the number this spec exists to move, and it is the argument for ranking
criteria by rounds-to-pass rather than by how interesting they are to build.

Two things the shape of it says, beyond the headline. The tail is the problem
rather than the median: 20.5% at five rounds or more is over twice their
starting figure while the mean is only a quarter above it, so a minority of
pull requests is absorbing the loop. And eleven of the 44 have not passed at
all, at up to ten rounds spent — excluded from the mean by definition, which
is why this table is reported beside them rather than alone.

The mean is `2.64` and not `1.32` partly for reasons nothing in the review
model controls: #1449 is a harness defect that raises a blocking finding on
**every** pull request editing `.claude/` or `CLAUDE.md`, which in this
repository is how conventions ship. A false finding is a whole round. Re-take
this reading after it lands; a baseline measured across a known artefact is a
baseline that will appear to improve for the wrong reason.

#### The re-take, 2026-10-24 — the baseline has NOT moved

#1449 and #1452 landed at 2026-10-23T21:46Z. Re-read over the 45 most recent
pull requests, **45 measured, 0 unmeasured**, and no ledger truncated, so no
round fell off the front of a window:

| | their before | their after | us, 2026-10-23 | **us, 2026-10-24** |
|---|---|---|---|---|
| passed after one round | 65% | 78% | 39.4% | **44.2%** |
| five or more rounds | 8.9% | 1.5% | 20.5% | **20.0%** |
| mean rounds to pass | 2.08 | 1.32 | 2.64 | **2.65** |

The tail did not collapse. Phases 1 and 2 keep their ordering, and the
argument for it is inherited rather than remade.

##### The split that says the opposite, and why it is wrong

Splitting that population at the moment the fix landed looks decisive, and
reporting it would have been a mistake:

| | pre-fix (31) | post-fix (14) |
|---|---|---|
| passed after one round | 30.0% | **76.9%** |
| five or more rounds | 25.8% | **7.1%** |
| mean rounds to pass | 3.07 | **1.69** |

76.9% against a target of 78% reads as the thing this document said would
invalidate its own plan. **It is an artefact of cohort age.** Rounds
accumulate over a pull request's life, and the two cohorts are not the same
age: pre-fix spans 4.5–9.2h old, post-fix 0.5–4.1h. A younger cohort shows
fewer rounds whether or not anything improved.

Counting rounds inside a fixed window from each pull request's **own**
creation, and including only pull requests that have actually reached that
age, so both cohorts are read at the same point in their own lives:

| window | pre n | pre mean | post n | post mean |
|---|---|---|---|---|
| 1h | 31 | 0.81 | 12 | **1.75** |
| 2h | 31 | 0.84 | 9 | **1.67** |
| 3h | 31 | 1.13 | 5 | 1.00 |
| 4h | 31 | 1.35 | 1 | 1.00 |

At matched age the improvement is **absent**, and at the two windows with a
usable `n` the post-fix cohort is accumulating rounds slightly faster. Read
that direction as noise rather than as harm: `n` is 12 and 9, and the cohorts
differ in what work they carry as well as in when they started. What the rows
will not support is the headline the naive split offers.

The 3h and 4h rows are reported because they exist and are read as nothing:
at `n` of 5 and 1 they are a sample size, not a measurement.

**The lesson is the one this document keeps relearning.** A reading taken
four hours after a fix lands is a reading about the four hours, and *"the
fix has landed"* is not the same precondition as *"the population has turned
over"*. The re-take instruction below asked for the first and meant the
second. Re-take again when the post-fix cohort has reached the age of the
pre-fix one — that is a question about elapsed time, not about what else
ships.

#### 41% of our rounds were rounds in which no review happened — read 2026-10-24

The ledger distinguishes a round that was **read and found nothing**
(`findings: []`) from one that was **NOT MEASURED** (`findings: null` — the
payload was absent or unparseable), and its own comment says they are
different facts. `readLedger` normalises the pair into a `measured` boolean.
Nothing had ever aggregated it. Over the same 45 pull requests, 117 rounds:

| | rounds | share |
|---|---|---|
| a review happened | 69 | 59.0% |
| **UNMEASURED** | **48** | **41.0%** |

18 of 45 pull requests are hit at least once, and **six were never measured
in their entire lives** — at 6, 6, 5, 5, 3 and 1 rounds each.

That matters because **CRC-M11 counts rounds and the 1.32 target counts
reviews**, and those have been the same quantity only by assumption. Scoring
the same 43 passed pull requests both ways:

| | all rounds | measured only | target | their *before* |
|---|---|---|---|---|
| mean to pass | **2.65** | **1.58** | 1.32 | 2.08 |
| passed after one | 44.2% | 62.8% | 78% | 65% |
| five or more | 20.0% | 4.4% | 1.5% | 8.9% |

**The measured-only column here is left as published and should not be
quoted** — the 2026-10-27 re-take below found the rule that built it scores a
pull request with zero measured rounds as a one-round pass, and this row
names six such pull requests two paragraphs up. `62.8% × 43 = 27.0` exactly,
so the defect is almost certainly present; it cannot be confirmed, because
the window rolled and the cohort is gone. It is left in place rather than
recomputed or deleted because **Phase 1's number thresholds were set from
it** and a reader needs to see what they were set from. The all-rounds
column is unaffected.

**So "we are worse than the state they were improving from, on all three" is
an artefact of the unit.** On review rounds we are better than their before
on two of the three — 1.58 against 2.08, 4.4% against 8.9% — and a shade
under it on the third. The sentence above this one stays unedited because it
is true of the number it describes; what is corrected is which number
answers the question.

**That conclusion did not survive the re-take, and the correction is not the
unit.** Rebuilt on the same cohort with the zero-measured pull requests
refused rather than scored, the 2026-10-27 measured-only reading is 3.03,
48.4% and 25.8% — **worse than their before on all three**, which is what
this paragraph said was an artefact. The unit distinction below is still
right and still worth having; what it cannot do is carry the verdict, because
the measured-only column was wrong on its own terms and not merely on a
different scale.

Both figures are real and they measure different things. **2.65 is the cost
to a developer** — every unmeasured round is still a red required check, a
re-run and a wait. **1.58 is the review convergence** this document's
mechanisms can move. Conflating them points the whole plan at the smaller
half of its own problem.

##### The 48 split cleanly, and the split names the two fixes

| | PRs | rounds | what it is |
|---|---|---|---|
| diff touches `.github/workflows/` | 5 | 25 | **structural decline** — the action refuses to review a workflow against a copy differing from the default branch |
| diff touches no workflow | 13 | 23 | **the no-payload tax** (#1478) — the reviewer runs to completion, exits `success`, writes nothing |

All five workflow-editing pull requests are in the never-measured six, at
100% of their rounds each. That is not a tax, it is a category of change
this repository cannot review at all, absorbing 25 rounds to produce zero
readings.

The other 23 are #1478, and it is not a size or complexity effect: three
observations now span a 9,000-line file, a 250-line four-file diff and a
**single prose-only markdown file**, all exiting `subtype: success`,
`is_error: false`, at 33, 53 and 32 turns against a cap of 80.

**The ordering consequence, stated plainly.** The largest single lever on
2.65 is not any CRC-B or CRC-E criterion. It is the 41% of rounds that
produced no review, and neither half of it is a review-quality problem.
Phases 1 and 2 keep their internal order — the measured-round tail did not
collapse — but nothing in them competes with fixing an instrument that is
silent two rounds in five.

**That consequence was correct and was not acted on, which is the finding the
re-take below is really about.** Everything merged between it and 2026-10-27
— Increments 1a, 1b and 1c — served Phases 1 and 2. Nothing served the 41%.
The paragraph above is three days old and reads as a decision; it was a
sentence.

##### How this was measured, and the near-miss that nearly published

`readLedger` and its `measured` flag, not a hand parse. The first attempt
used a hand-rolled `indexOf("```json")` and **silently returned zero rounds
for 17 of 43 pull requests**, under-counting the population by 44 rounds
while reporting a confident 53.4%. It was caught only because its mean
(1.67) disagreed with `summariseRoundsToPass` (2.65) on the same input.

That is this repository's fourth shape — a second decider for a question
that already had one — and it failed open to an empty list that reads as
data. **The ALL-rounds column above reconciles exactly with
`bun evals/ai-review-control/run.ts rounds` on the same file: 2.65, 44.2%,
20.0%.** That agreement is the only reason the measured-only column is
reportable, and a reading of this kind should not be published without it.

#### The re-take, 2026-10-27 — both halves grew, and the decline half doubled

Read over **#1573–#1631 — a pull-request RANGE, not "the 45 most recent"**,
with 45 ledgers found, 0 unmeasured and 178 rounds. The window rolls: re-run
this an hour later and `first:45` has dropped #1573 and taken in whatever
opened since, which moves every figure for reasons that have nothing to do
with the work. **A reading of this table is only comparable to another one if
both name their range**, and the two readings above this one do not.

```sh
bun scripts/crc-reading.ts --lo 1573 --hi 1632 --record
```

**That command is the whole reading, and until #1633 it was four.** The fetch,
both premise guards, both scoring columns, the round-kind split and the
dated store are one program with a battery
(`test/crc-reading.test.ts`). What follows in this section is the argument
for each of those pieces, kept because every one of them was arrived at by
getting it wrong first; the figures themselves are rendered from
`specs/crc-readings.json` and are no longer retyped.

**Why a program and not four commands — three reasons, all observed.** `jq`
walks a list with one filter, so **a single malformed ledger aborted the
pipeline and lost the entire range** rather than refusing one pull request.
The recipe's fence rule, `split("```json")[1] | split("```")[0]`, **cut
itself in half**: on 2026-10-27 it cut a 27,252-character ledger at 18,021,
and the text at the cut was a reviewer quoting this very recipe into a
finding, so any pull request whose review discussed the measurement broke the
measurement. And the table below it was **retyped on every reading**, which
is how it twice carried figures built by a rule the prose beside them had
already abandoned.

**The fetch is in the chain too, and the reason is not the one the reviewer
gave.** It was raised that an unchained `gh api` would leave the guards
validating leftover data from an earlier run. That cannot happen, and each
leg was checked rather than argued: `>` truncates before the command runs,
so there is no stale file; an **empty** file exits 4 at the first `jq -e`; a
**partial** one dies on `Unfinished JSON term at EOF`; and a **valid but
empty** array — the one shape that clears the first guard, which it does,
returning true — is refused by the range guard, because `[] | min` is `null`
and `null == 1573` is false. All three failure shapes are already loud.

The chain is added anyway. A fetch whose failure is caught only because
three downstream accidents happen to cover its three failure shapes is
working by luck, and the next edit to any of those guards removes a
protection nobody wrote down. One `\` makes the dependency the reader can
see. That it was missing at all is the same defect as round 2's, one line
higher up and left behind by the fix.

**The range is a filter, not a page size, and the first draft of this block
confused the two.** It fetched `first:45` and called the result #1573–#1631,
which is the rolling window wearing a range's clothes: re-run it an hour
later and the same command returns a different cohort under the same label.
The fix is to over-fetch and `select` the range, and the second `jq -e`
asserts the page actually reached both ends — an under-sized `first:N`
silently returns a prefix of the range, which is the same failure one level
down.

**The `&&` is load-bearing and the first draft of this block did not have
it.** Three statements in a fence are three independent commands: a failing
`jq -e` printed a signal and the read ran anyway, so the guard gated nothing.
A check whose refusal nothing consumes is the defect
`.claude/rules/checks-must-be-able-to-fail.md` is named for, and it arrived
inside the pull request that re-measures a document about it. Chained, the
refusal stops the read.

**What the guard refuses is narrower than "the page was full", and the first
draft got the mechanism wrong.** The ledger is **one upserted comment**
(`AI_REVIEW_PERSIST_STEP_ID`, #1168) — every round edits it rather than
adding one — so its position in GitHub's creation-ordered connection is fixed
when round 1 writes it, and no later volume can push it past the hundredth.
On #1597, twelve rounds and nine comments, the ledger is at **index 0**. The
first draft said a pull request could become "busy" and lose its ledger off
the end; that cannot happen. The only way the ledger sits past position 100
is **100 other comments existing before the first review round ever ran**,
and the only genuinely ambiguous reading is a pull request with a **full page
and no ledger found** — absent and not-read are the same bytes there. A full
page with a ledger found is fine, and a short page with no ledger is a real
absence. The guard now asks exactly that question; the version this replaced
refused the full-page case outright and would have fired on pull requests it
had read correctly.

**It is also not the only premise check in the recipe**, which is why the
narrow form is safe. `run.ts rounds` opens with
`rounds-to-pass: measured N, unmeasured M` over the same file and then names
every unmeasured pull request individually, and a `body` of `null` lands
there as `UNMEASURED LEDGER_ABSENT` rather than as a review that happened
once (`roundsTaken`, `lib/rounds-to-pass.ts`). So the fetch's guard and the
parser's refusal answer the same question from two sides: the guard refuses
the case where absence is unresolvable, and the parser refuses to score the
absence either way.

**`author.login == "github-actions"` is correct here and wrong one API
over.** GraphQL's `Actor.login` for the built-in Actions bot is
`github-actions`; REST's `user.login` for the same comment is
`github-actions[bot]`. Both were read on #1630 to settle it. Transcribing
this filter to a REST call silently matches nothing and returns 45 empty
bodies, which is the same shape as the truncation above: a reading of zero
that looks like data.

Everything between the two markers below is **rendered from the last row of
`specs/crc-readings.json`** by `renderCrcReading`, and
`test/crc-reading-spec-parity.test.ts` fails if the two differ. Editing it by
hand is reverted by the next reading; that is the point, and the two wrong
figures this section has published were both retypings.

<!-- crc-reading:begin — generated by `bun scripts/crc-reading.ts`; do not edit by hand -->

Read over **#1573–#1632** on 2026-10-27 — 46 pull requests, 189 rounds.

| | all rounds | numerator | measured rounds only | numerator |
|---|---|---|---|---|
| mean rounds to pass | 4.34 | 191 / 44 | 3.22 | 103 / 32 |
| passed after one round | 27.3% | 12 / 44 | 46.9% | 15 / 32 |
| 5 or more rounds | 37.0% | 17 / 46 | 27.3% | 9 / 33 |

The five-or-more row's denominator is ALL measured pull requests and the two above it are over the ones that PASSED, in both columns — a tail measured on survivors only has had its tail cut off.

| round outcome | rounds | share |
|---|---|---|
| `measured` | 105 | 55.6% |
| `declined` | 47 | 24.9% |
| `no_payload` | 36 | 19.0% |
| `log_unreadable` | 1 | 0.5% |

**The measured-only column is a LOWER BOUND.** 6 round(s) were evicted from ledgers that scored in it, and an evicted round's kind is unrecoverable.

**13 pull request(s) had zero measured rounds in their entire lives** and are UNMEASURED in the measured-only column rather than scored as one-round passes: #1589, #1593, #1596, #1598, #1599, #1602, #1610, #1613, #1615, #1621, #1623, #1628, #1629.

<!-- crc-reading:end -->

The historical columns stay here because the store's first row is
2026-10-27 and a comparison needs something to compare against. **They are
not re-derivable** — the window had already rolled — and the 10-23 and 10-24
columns were built by the rule the correction below withdrew:

| | their before | their after | 10-23 | 10-24 |
|---|---|---|---|---|
| mean rounds to pass | 2.08 | 1.32 | 2.64 | 2.65 |
| passed after one round | 65% | 78% | 39.4% | 44.2% |
| five or more rounds | 8.9% | 1.5% | 20.5% | 20.0% |

**Both columns now use the same denominators, and that moved one published
figure.** The hand-run measured-only column put all three of its figures over
merged pull requests; `scoreColumn` applies `lib/rounds-to-pass.ts`'s rule to
both columns — mean and one-round over the pull requests that PASSED, the
five-or-more tail over ALL measured ones. So the measured-only tail now
carries still-open pull requests with at least one measured round, which is
exactly the population the tail exists to find, and the 2026-10-27 figure
reads 9 of 33 rather than the 8 of 31 published by hand. Both numerators are
in the table so the change is visible rather than argued.

**The zero-measured list grew by one for the same kind of reason.** The hand
count said twelve and named only MERGED pull requests without saying so; the
script counts every pull request in the range, so #1599 — open, two rounds,
neither reviewed — is the thirteenth.

**The last row has a different denominator from the two above it, and the
column did not say so until the reviewer could not reproduce it.** No integer
over 43 rounds to 35.6% — 15 of 43 is 34.9% and 16 of 43 is 37.2%, with
nothing between them — so a reader checking this cell against the 43 merged pull
requests the other two rows use gets a number that matches no count. The 45
is deliberate and is `formatRoundsToPass`'s own choice: the mean and the
one-round rate are over pull requests that **passed**, and the tail is over
**all measured**, passed or not, because *"a tail measured on survivors only
has had its tail cut off"*. Over passed only it would be 16 of 43, 37.2%. The
numerator column is now part of the table rather than a sentence under it,
which is the only form of this that a reader can check without rerunning
anything.

**The headline is the wrong unit, for the same reason it was on 2026-10-24,
and the split is the reading.** Of the 178 rounds — **all 45 pull requests in
the range, merged or not**, which is a different population from the 43 the
measured-only column below uses, and the reason this table says 96 measured
where that one counts 94. The two still-open pull requests contribute the
difference: #1607 has 2 measured rounds and #1599 has none. Neither figure is
stale; they answer different questions, and until this sentence existed a
reader had no way to tell that from the document.

The round-kind split is in the generated block above, and **UNMEASURED is
the whole difference between the two scoring columns.**

> **THE KNOWN GAP IS CLOSED, and it fired on live data before it was.** This
> section used to carry a `jq` recipe with a declared gap: a malformed ledger
> aborted it on *"Unfinished JSON term at EOF"* or *"Cannot iterate over
> null"*, and **the whole range was lost rather than the one pull request**.
> On 2026-10-27 it fired from a **third** cause the caveat did not name —
> `split("```json")[1] | split("```")[0]` cut a ledger at a reviewer's quoted
> fence, 18,021 characters into 27,252 — and the quoted text was the recipe
> itself. `measuredRoundsFor` refuses per pull request and
> `test/crc-reading.test.ts` holds all three shapes, the third built from the
> payload that produced it. **A caveat naming two causes did not cover the
> third**, which is the argument for a battery over a blockquote.

**The `if` was not defensive padding — without it the all-refused case was a
jq crash, and the reviewer found it in this recipe.** `[] | add` is `null`,
and `null / 0` aborts with *"null (null) and number (0) cannot be divided"*
at exit 5. So a range in which the review system refused **every** merged
pull request — the end state this document is tracking toward, not a
hypothetical — would have reported a stack trace where it should report
`UNMEASURED`. That is the *Silent Default Substitution* failure in its
loudest form: the one reading that most needs to be legible is the one the
instrument could not print.

**`select(.findings != null)` replaced `select(.unmeasured == null)`, and
the reason is which writer each one trusts.** A ledger round is written
twice. `lib/scaffold/ai-review-step.ts` emits
`{at, sha, merge, run, attempt, identity, round, turns, verdict, findings}`
and **no `unmeasured` key at all**; `lib/ai-review-unmeasured.ts` then adds
one in a second pass — `{ ...round, [AI_REVIEW_LEDGER_UNMEASURED_KEY]: state }`,
declared there as *"additive beside `findings`, never instead of it"*. So
`.unmeasured == null` is a question about whether the **second** pass ran,
and `.findings != null` is a question about the round itself. A round the
recorder never reached would carry neither key and be scored as measured.

Measured over all 178 rounds in the range, the ledger has exactly two
shapes — **96 with no `unmeasured` key and `findings` an array, 82 with the
key and `findings: null`** — so the two predicates are complementary here and
**zero rounds are mis-scored by either**. The swap changes no published
figure. It removes a dependency on a workflow that is not the one being
measured.

**An earlier round of this pull request raised this and the reason given for
declining it was wrong.** The reviewer proposed `.findings != null`; the
answer was that the two predicates provably agree, so swapping one for the
other buys nothing but a second decider. The agreement was real and the
inference from it was not: the right question was never which predicate is
*correct today*, it was **how many writers each one depends on**. That is a
property no amount of agreement on current data can show.

**Those are the second set of figures this paragraph has carried, and the
first set were wrong in a way that flattered every column.** It published
*2.19 mean, 27 of 43 after one round (62.8%), 8 of 43 at five or more
(18.6%)* over a denominator of 43, while stating three paragraphs below that
**twelve of those 43 had zero measured rounds in their entire lives**. Both
halves cannot hold. The reviewer put the dilemma on this pull request —
either the twelve are included at some default count, or the denominator is
31 — and the first horn is what happened:

- `94 / 43 = 2.19`, so the twelve entered the mean **as zeros**, pulling it
  down by 0.85.
- `27 = 15 + 12`. Fifteen pull requests had exactly one measured round; the
  other twelve had **none**. A pull request the reviewer never read once was
  counted as a one-round pass, which is the single most favourable thing this
  document could have said about a pull request the review system refused.
- `8` was right and `43` was not, so the tail was understated at 18.6%
  against a true 25.8%.

A pull request with zero measured rounds has no rounds-to-pass under this
metric, and the convention for that is already in the tree: `roundsTaken`
refuses a pull request with no readable ledger as `LEDGER_ABSENT` rather than
scoring it as zero. **The twelve are UNMEASURED here for the same reason, and
they are reported beside the number rather than inside it.**

**The reviewer's round-1 smell was correct and the verdict this paragraph
gave it — "coincidence" — is withdrawn.** The flag was that 62.8% was
byte-identical to the 2026-10-24 measured-only figure while both companions
moved a long way, over two cohorts this document says barely overlap. The
answer given was that `27 / 43 = 62.79%`, computed twice by different
parsers. Both parsers were applying the same rule, so they were **one
decider**, and the agreement they produced was the defect reproducing rather
than the figure being confirmed —
`.claude/rules/checks-must-be-able-to-fail.md`, *two deciders that agree*. A
reconciliation that cannot disagree is not a reconciliation; the parsers have
to be given the case they are meant to differ on, and the case here was a
pull request with zero measured rounds.

**The 2026-10-24 row inherits the construction and cannot be recomputed.**
`62.8% × 43 = 27.0` exactly there too, over a reading that names **six**
never-measured pull requests, so its one-round count is very likely `21 + 6`
and its mean very likely carries six zeros. That is an inference, not a
reading: the window rolled, the cohort is gone, and nothing in this document
can settle it. It matters because **Phase 1's number thresholds (1.58 and
4.4%) were set from that row** — see the phase table — so they are thresholds
derived by the rule this section just stopped using, and comparing 3.03
against 1.58 compares two different arithmetics. The thresholds need
re-deriving; that is a change to the phase table and not to this reading.

**The decline is attributable to workflow-editing diffs, and the control is
counted rather than asserted:**

| diff | PRs | rounds | declined |
|---|---|---|---|
| touches `.github/workflows/` | 14 | 60 | **46 — 76.7%** |
| touches no workflow | 31 | 118 | **1 — 0.8%** |

The single exception is #1597, one decline in twelve rounds. It is named
rather than absorbed, and the obvious hypothesis — the guard compares against
the default branch *at run time*, so somebody else's workflow merging to
`main` can make an unchanged pull request mismatch — is a **hypothesis and not
a reading**, because nothing here establishes what `main` held at that
moment. Two of the fourteen workflow-editing pull requests drew no decline at
all, so the mechanism is not deterministic on the diff either.

**Twelve of the 43 merged pull requests had zero measured rounds in their
entire lives**, and all twelve changed at least one file under
`.github/workflows/` (`gh api repos/hornjason/pai-harness/pulls/<N>/files`):

> #1589, #1593, #1596, #1598, #1602, #1610, #1613, #1615, #1621, #1623,
> #1628, #1629

**#1621, #1623 and #1629 are Increment 1.** The suppression gate this
document ordered first, built over three pull requests, merged without a
single round producing a payload. The change that edits the reviewer is the
change the reviewer refuses to read, and that is not a tax on the metric — it
is an unreviewed hole sitting exactly where the highest-risk changes in this
repository go.

**What would falsify this.** A decline on a pull request touching no workflow
file, at a rate anywhere near 76.7% — the 0.8% column is the control and it is
one round in 118. Or a workflow-editing pull request whose rounds are
measured, at a rate that makes 76.7% look like sampling: two of fourteen
already are, so the claim is about the rate and not about every member, and
anyone can re-run the two commands and disagree with the arithmetic.

**Three things this reading does NOT establish, each of which leans toward the
conclusion the author wanted.** The 10-24 and 10-27 windows barely overlap, so
2.65→4.19 compares two largely disjoint cohorts rather than tracking one.
The measured-only 1.58→3.03 has the same problem and a worse one on top of
it — the two sides are built by different rules, per the correction above —
so it is suggestive at most. And the author's own pull requests sit in the tail at 8, 9 and 12
rounds; the obvious explanation — that this document's own spec work is prose
and prose draws rounds — **was tested and does not hold**: markdown-only pull
requests mean 3.86 rounds against 3.97 for everything else. The regression is
broad.

**Reconciled across two parsers — and the first attempt at this was not a
reconciliation.** The split (96 / 47 / 34 / 1), the measured-only column and
the twelve were computed with `jq` and again in a separate program, and they
agree. That is worth exactly as much as the two programs' rules differ, and
on the first attempt they did not differ at all: both scored a pull request
with zero measured rounds as a zero-round, one-round pass, so the agreement
confirmed nothing and the figure shipped wrong. **Name the input two parsers
must disagree on before quoting their agreement.** Here it is a pull request
whose every round is `declined`, and the corrected pair are given it
explicitly: one treats it as UNMEASURED, one scores it as zero, and the
13-point spread between 48.4% and 62.8% is what that single decision is
worth. `run.ts rounds` supplies the ALL-rounds column from the same input and
reproduces 4.19 / 27.9% / 35.6% on the named range.

**Two caveats the arithmetic carries.** The ledger on #1614 evicted five
rounds and on #1597 one, and an evicted round's kind is unrecoverable, so
**94 measured rounds is a lower bound and 3.03 could be as high as 3.23**.
Neither pull request can move the other two figures: both sit at nine
measured rounds, already inside the five-or-more bucket and nowhere near the
one-round one. And the eviction count is read from the ledger's own
`truncated` field rather than assumed to be zero — `174 + 6 = 180`, and
`180 / 43 = 4.19`, which is how the ALL-rounds column reconciles with a file
holding 174 rounds.

### What stays human

- [ ] CRC-H1: Direction, taste and scope — whether to build it at all.
      needs: review
- [ ] CRC-H2: Risky code — billing, auto-updater, CI workflows.
      needs: review
- [ ] CRC-H3: Architecture that sets a pattern others copy.
      needs: review
- [ ] CRC-H4: Reading the evidence. **"If you can't say what the checks would miss, ask for a real review rather than a quick approval."**
      needs: review
- [ ] CRC-H5: Owning the outcome — a person is accountable for every change that ships, whoever typed it.
      needs: review

## What an unticked box means here

Audited criterion by criterion on 2026-10-23. A spec nothing is bound to
cannot drift, because there is nothing for it to drift from; what replaces
that is the per-criterion placement in the sections below, which a test
reads.

**The per-bucket tally that stood here has been deleted rather than
corrected, and that is the repair.** It enumerated how many criteria sat in
each of seven buckets. Nothing derived those figures, so every criterion
that changed bucket falsified them silently: they drifted four times, and
**five consecutive review rounds each found a different miscount** — the
total, the unobservable count, the deviations row, and then two defects in
the guard written to stop it. Each repair fixed the sentence that round
happened to construct.

That is the defect class this spec's own CRC-N3 section is about, committed
here by its author, and the two failed repairs are worth naming because both
were narrower than the thing they guarded. Restating the figures as a
*dated* reading still left seven hand-written numbers in prose. Guarding
them with a regex over three bucket names missed the other four spellings.

**The counts are now derived or absent.** `bun bin/rungate.ts audit-specs`
reports them, and the sections below are the per-criterion truth. A number
that lives in one place and is computed cannot disagree with itself.

**A document-wide guard was then proposed twice, and measurement refuses
both.** Review round 7 asked for one check over the whole body requiring
every bold-faced count to resolve to a computed source. Counted, that is
168 bolded spans carrying a digit outside tables, nearly all of them
criterion ids, issue numbers and dates:

```sh
grep -vE '^\s*\|' specs/CODE-REVIEW-CONVERGENCE-SPEC.md \
  | grep -oE '\*\*[^*]*[0-9][^*]*\*\*' | wc -l
```

The narrower hypothesis — that every instance found so far is a
*restatement*, so no cardinal may appear twice in prose — fails the same
way. Stripping criterion ids, issue numbers, dates, times, percentages and
code spans still leaves 57 distinct cardinals occurring more than once, and
the dense end of that distribution is ordinary English rather than
measurement. Both readings are commands, not assertions, and both can be
re-taken against whatever this file says today.

**A third variant was proposed on 2026-10-28 and is refused by CLASS, not
by cost.** Round 7 of #1637 asked for one scanner over the whole body,
minus frontmatter and fenced code, demanding a date or a command from every
block stating a bare multi-digit number — on the correct observation that
hand-picking sections is the recurring failure mode rather than the
particular section picked.

**The figure first published here — 292 blocks, 136 stating a number, 63
without provenance — is WITHDRAWN, and its withdrawal is this rule proving
itself on its own paragraph.** It was written with a date and no command, so
when round 10 asked for the command there was nothing to re-run: the count
could not be reproduced, and nobody reading it could have told. Re-taken
2026-10-28 against the same revision it described, with the command recorded
this time:

```sh
git show e7e12ed9:specs/CODE-REVIEW-CONVERGENCE-SPEC.md > /tmp/body.md
bun -e 'const fs=require("fs");
let d=fs.readFileSync("/tmp/body.md","utf-8")
  .replace(/^---\n[\s\S]*?\n---\n/,"").replace(/```[\s\S]*?```/g,"");
const blocks=d.split(/\n\s*\n/).map(s=>s.trim()).filter(Boolean)
  .filter(b=>!/^#{1,6} /.test(b) && !/^\|/.test(b));
const withNum=blocks.filter(b=>/\b\d{2,}\b/.test(b));
const noProv=withNum.filter(b=>!/\b20\d\d-\d\d-\d\d\b|`[^`]*\b(bun|gh|git|grep|npm|node)\b[^`]*`|\brun \d|\b[0-9a-f]{7,40}\b/.test(b));
console.log(blocks.length, withNum.length, noProv.length)'
```

**240 non-heading, non-table blocks, 129 stating a number, 68 naming no date,
run, commit or command.** 68 is a payable price. The
reason it is still wrong is the table above: re-takeability is the
**world-derived** rule. A large share of those 63 are document-derived — the
47/30 split, the bullet tallies, every figure a guard in
`test/code-review-convergence-spec.test.ts` already recomputes — or cited,
like Tricorder's thresholds and the 65% → 78% target this document is aimed
at. Demanding a date and a command from those two classes asks the wrong
question of them, and a guard that is wrong about most of what it fires on
is routed around within a week. That judgement does not depend on which of
the two counts is right: 63 and 68 are the same order and the same argument.

**A fourth variant was proposed on 2026-10-28 and is accepted as a class,
deferred as an instrument, with the measurement here so the next round reads
it rather than re-deriving it.** Round 9 of #1637 observed that the recurring
defect across rounds 2 through 9 is one class: *a prose claim about something
EXTERNAL to this document — another document's practice, what a named `lib/`
module compares, whether a baseline carries a date — is asserted from memory
and corrected only after a reviewer re-reads the source.* That is right, and
it names four instances this document already records, including CRC-M15
being wrong three times. Its proposed remedy is that such a claim should cite
what it describes.

The mechanism for that **already exists and is proven**: `lib/source-anchor.ts`
resolves a citation written as a source path, an `@`, and a quoted snippet of
the line meant, to exactly one site or it refuses — `ANCHOR_CITATION` is the
pattern and `resolveCitation` the resolver. `specs/GATE-CONTRACTS-SPEC.md` is
bound to it — where three of the four
citations outside the guard were already wrong when it was built. So the
generaliser is not a new instrument; it is giving that one something to
resolve. Taken 2026-10-28 against `a6d79e17`, the commit that first carried
this paragraph:

```sh
git show a6d79e17:specs/CODE-REVIEW-CONVERGENCE-SPEC.md > /tmp/doc.md
bun -e 'const fs=require("fs");
const d=fs.readFileSync("/tmp/doc.md","utf-8");
const m=[...d.matchAll(/`((?:lib|scripts|gates|hooks|test|workflows)\/[A-Za-z0-9_.\/-]+\.(?:ts|js|json|md))`/g)].map(x=>x[1]);
console.log(m.length, new Set(m).size,
  [...new Set(m)].filter(f=>!fs.existsSync(f)).length)'
```

**75 backticked mentions of a source path, across 39 distinct files, every
one of which exists on disk, and ZERO citations in the resolvable anchor
form.** Pointing `citationFailures()` at this document passes while reading
nothing — a vacuous green, which is the shape this spec exists to refuse.

**This figure was first published as 73 across 38, and the correction is
worth more than the number.** The reading was taken, and then this paragraph
was written — and the paragraph names two more source paths, so the file it
described no longer existed by the time the sentence about it was committed.
A world reading that does not name the revision it was taken against will
drift from the document that carries it, in the direction of the author's own
edit, with nothing able to notice. That is the whole argument for naming a
revision and a command rather than only a date.

**The cheap proxy was measured and is refused on its error rate**, which is
why this is deferred rather than shipped in the round it was raised. Inferring
the attribution instead of requiring it — charging every backticked identifier
in a paragraph to the one source file that paragraph names — yields three
claims here and **one false of the three**: `review_scope_for_round()` is a
shell function in the generated `ai-review-carry` step and the sentence says
so, but the same paragraph also names `lib/ai-review-rounds.ts`, so proximity
charges it there. A guard wrong about a third of what it fires on is routed
around within a week. The attribution has to be written by the author in the
anchor form, which makes this a pass over 73 sentences — a piece of work, not
a review round.

That is also why the **section census** below is the right generaliser and a
whole-body number scan is not: the census asks whether a section is
ACCOUNTED FOR, so each section declares which class governs its numbers,
rather than one rule being applied to three classes that owe different
things.

So the class is real and it is not closable by a guard over this file at a
price worth paying. It is a property of the genre — a long hand-written
document that restates its own measurements — and the honest scope for
closing it is moving every measurement into one generated section, which is
a piece of work rather than a review round. The guards that exist bind the
regions where a restatement has actually been found, and that is stated as
a floor, not as coverage.

**The next instrument is a section census, and it is specified here rather
than built here.** It asserts that every heading is either read by a guard
in `test/code-review-convergence-spec.test.ts` or carries a written reason
for not being — so adding a section turns the suite red until someone
decides which. It does not close the class; it converts a silent hole into
a loud one, which is the only move the measurements above leave open. Two
readings justify it and both were taken on 2026-10-27, by writing the
census, running it once, and removing it again:

```sh
grep -cE '^#{2,3} ' specs/CODE-REVIEW-CONVERGENCE-SPEC.md
```

At `##` granularity the census leaves most sections unaccounted on its first
run, including the one holding the prior-art bullets this round found wrong.
And `##` is the wrong granularity: `untickedBoxSection` and
`remainderSection` both read sub-sections of *the same* `##`, whose bulk is
read by neither, so a census at that level would report coverage the guards
do not have. The honest unit is the `###`, which the command above counts.
That scale — not the principle — is why this is separate work: introducing
a new instrument at round 8 of a three-round budget, in the document that
criticises exactly that, would be the behaviour rather than the fix.

Re-counted on 2026-10-23 after #1437 bound CRC-E1, CRC-E2 and CRC-E4, and
again after #1448 bound CRC-M11; re-counted on 2026-10-24 after #1587 bound
CRC-B7, which moved one criterion out of *not done* and no other category. The audit above was taken the same day, at 0
bound; the four moved by engineering, and none of the other four categories
changed, which is the point of keeping them separate.

Re-counted again on 2026-10-24 (#1469): CRC-F1 moved out of *blocked on an
owner decision* into a sixth state, **contested**, which did not exist
before and is not a refinement of the fifth. Nothing was ticked and nothing
was built; one criterion was re-described, because the description it had
was false in a way that cost a repo-wide outage.

An unticked box is one of the last six, and they are six different facts.
Five of them are recorded here because an unticked box nobody can ever tick,
one waiting on a person, one the repository itself argues both sides of, and
one nobody has started all look identical, and only the last is work.

The split is load-bearing rather than tidy: 47 unticked boxes read as 47
pieces of engineering. Seventeen of them are not engineering at all.

### A mechanism exists; this repository cannot observe it

Do not tick these, and do not count them as remaining work either.

| Criterion | What exists | Why no test here can read it |
|---|---|---|
| CRC-C1 | The security review runs as a local Claude Code plugin an agent invokes per session. | It is not repo CI. `.github/workflows/` contains no security pass, so no artefact in this tree records that one ran. |
| CRC-C2 | **The bug-review half holds.** `test` and `ai-review` are required contexts on `main` with `enforce_admins` on, so a blocking finding reds the check and the merge is refused. Read from the API on 2026-10-23. | Branch protection is GitHub state, not tree state. The security-review half does not hold at all — there is no security check to require. **`required_conversation_resolution` is `true`** (read 2026-10-25; this cell said `false` until then), so an open thread DOES block. **The producer has since landed** (2026-10-26): the generated workflow's step `Post this round's findings onto the diff` runs `ai-review-threads`, and #1614 carries four `github-actions`-authored review threads. The security-review half still does not hold, for its own reason — there is no security check to require — so the verdict is unchanged, but it no longer rests on the absent-producer claim. |
| CRC-M2 | `REVIEW_OUTCOME_PLANTS` holds four findings whose outcome was established independently. | Expert confirmation is a human act, and those four grade the outcome sweep rather than an incident case set. |
| CRC-N3 | `REVIEW.md` asks for the class and not the line, and CRC-A6's check proves the reviewer read it. **An artefact now exists**: #1614's ledger round 12 raised a finding against `lib/review-tool-agreement.ts` whose summary is the class itself — that each prior fix "closed the one bypass shape a reviewer happened to construct that round rather than a general property" — and recommended a structural parse over the hand-rolled regex. Round 13 records the recommendation carried out and the class closed. | Whether it complied is still a property of a sampled model, and **one instance is not a rate**. The cell no longer rests on *no artefact exists*; it rests on there being no denominator. The instance also arrived at **round 12 of 15**, so it is evidence the behaviour is reachable, not evidence it is timely — see *The author-side half of CRC-N3* below. |
| CRC-H1, CRC-H3, CRC-H4, CRC-H5 | Statements about human judgement. | Nothing distinguishes them being honoured from them being ignored. |
| CRC-N2 | **Adopted in #1600, and it moved here out of *Deliberately not adopted*.** The generated `ai-review-carry` step writes `review_scope=diff` from round 3 when the carry reading is complete, the prompt states both words, and the carried list is declared outside the scope so a prior finding whose file the diff does not touch is still raised. **Adoption was conditional on #1601 and the condition was met in the same change, not waived:** narrowing is only safe while the carry does not silently drop a finding, and until 2026-10-24 it did — the anchor was a line number. `review_scope=diff` is now reachable only when the carry read is complete AND the ledger records no truncation AND the prior rounds are `1..r-1` with no hole; every other reading answers `full`. | **The scope is a WORD, and whether the reviewer confines its reads to it is a BEHAVIOUR.** #1533 measured the reviewer reading whole files rather than the diff. A narrowed round leaves no artefact distinguishing *the reviewer confined its reads* from *the reviewer was asked to and did not* — the step records the request; the reviewer's reads are recorded nowhere. See *Measured non-obvious facts* below. |

### The author-side half of CRC-N3 is unowned

CRC-N3 puts the duty on the **reviewer**: flag the class. CRC-A8 *would*
cover **cross-PR** recurrence — a repeated finding becoming a rule or a
lint — but **it is unticked and nothing implements it**: no path routes a
review finding into a skill, a lint rule or an instruction file, and
`lib/rule-promotion.ts` promotes from compliance failures rather than from
findings. So the cross-PR half is a plan, not a mechanism. Between
them sits the case that actually costs rounds here — **the author fixing one
instance of a class inside a single pull request, while the siblings sit
untouched in the same file** — and no criterion owns it.

#1614 is the worked instance, and it is unusually legible because the ledger
kept every round. Rounds 10, 11 and 12 each found a defect of **one class**:
hand-rolled regex reads of the `on:` and `if:` YAML in
`lib/review-tool-agreement.ts`. Nested keys over-matching, then a YAML merge
key under-matching, then a vacuous test control over the same function. Each
was repaired at the spelling the reviewer happened to construct. Round 12
named the class and recommended a structural parse; round 13 records that it
shipped and the class closed in one change.

**The reviewer got there. It took eleven rounds first.** That is the gap: not
that the class is never named, but that naming it is a sampled behaviour
competing with the much easier move of answering the instance in front of you.
The author-side obligation — *given one confirmed defect, enumerate the
population* — is the half nothing in this document requires.

#### What the industry calls this, and what it has built

The name is **variant analysis**: given one confirmed defect, find every
sibling. It is a mature practice and this repository has adopted none of it.

- **CodeQL** is the reference implementation. GitHub Security Lab passed
  **500 CVEs disclosed in open-source projects** and credits CodeQL for the
  pace ([GitHub blog, 2023][gh500]) — that figure covers all of the Lab's
  disclosures, and **no published figure isolates variant analysis alone**,
  so do not cite one. An earlier draft of this bullet claimed "400+ CVEs
  found by variant analysis"; it traced to a secondary blog post and was
  removed when the reviewer asked where it came from. CodeQL is free for
  public repositories and **has never been enabled here**: the code-scanning
  alerts API answers `no analysis found` for this repository, read on
  2026-10-27.

[gh500]: https://github.blog/security/vulnerability-research/the-github-security-labs-journey-to-disclosing-500-cves-in-open-source-projects/
- **Semgrep** covers the same move at lower cost for syntactic classes.
- **Trail of Bits' variant-analysis methodology** names *narrow scope —
  searching only the original module* as the first failure mode, which is
  exactly #1614's rounds 10 through 12.
- **Tricorder** (Sadowski et al., ICSE 2015, [paper][tri]) is the closest
  prior art to CRC-A8: review findings become executable analyzers, most
  contributed by the developer who hit the bug, governed by an **effective
  false-positive** budget — a report the user took no action on. Above
  **10%** the analyzer goes on probation and its author must show progress;
  above **25%** the Tricorder team may switch it off immediately. An earlier
  draft of this bullet said "<5% … and the analyzer is disabled", which is
  wrong in both the threshold and the consequence. The graduated contract is
  the part worth copying, and the probation tier is the half the wrong
  version lost: an analyzer nobody can switch off becomes an analyzer
  everybody clicks past, but one switched off at the first bad week never
  gets fixed.

[tri]: https://research.google/pubs/tricorder-building-a-program-analysis-ecosystem/

#### Build or adopt — the answer is mostly adopt, and the honest caveat

**Do not build a variant finder.** Three exist, one is free and unenabled.

| Need | Decision |
|---|---|
| find siblings of a defect in TypeScript | **adopt** CodeQL; it is free here and switched off |
| syntactic class sweeps | **adopt** Semgrep, or `rg` for a one-off |
| lint `run:` blocks in workflows | **adopt** actionlint — **and assert shellcheck is on PATH**, because with it absent actionlint skips every block and exits 0, which is a fail-open gate |
| require the author to state the population | **build** — nothing off the shelf does this, and it is small |

**The caveat, stated plainly: none of the adopted tools would have caught the
three defects found on #1621 and #1623.** Those are semantic claims about what
a command's exit code *means* — `if ! jq -e …` collapsing exit 1 and exit 5
into one observable — living in shell embedded in TypeScript template
literals. Neither CodeQL nor Semgrep parses that. Adopting them is still right,
because they cover classes we currently cannot see at all; it is not a fix for
the class this document keeps hitting.

#### The gate worth building, and the control that stops it being vacuous

Small, and it reuses the thread reader Increments **1a and 1b already
shipped** — the suppression gate's `pulls/{n}/comments` plus GraphQL
`isResolved` read (#1621) and carry-forward's read of the same (#1623).
That reader exists in the tree today, and so does the two-push evidence
that it does not duplicate (`AS-10`). What remains is 1c, the removal of
the ledger comment:

1. The reviewer tags every finding with **exactly one** of `class:<name>` or
   `instance-only`, and a `class:` tag names the search that finds the siblings.
2. The author's reply to a class-tagged thread must carry a population count —
   `N sites, M defective` — and the search that produced it.
3. A check refuses merge on a class-tagged thread **resolved without one**.
4. **An untagged finding refuses too.** Absence of a tag is UNMEASURED, not
   `instance-only`.

**Step 4 is the one the first draft of this section got wrong, and the
reviewer caught it on #1627.** As first written the check fired only on
threads already carrying `class:`, so never applying the tag bypassed the
whole mechanism with zero friction — the *detector narrower than what it
detects* shape `.claude/rules/checks-must-be-able-to-fail.md` warns about.
A gate whose trigger is optional is not a gate. The repair is the repo's
standing one: the unreadable state is a refusal, not a pass.

**Every state the tag field can be in, and what each must produce.** The
table is the vocabulary, so it is exhaustive by construction rather than by
a count stated beside it:

| Input | Required outcome | What it proves |
|---|---|---|
| `class:<name>`, resolved with no count | **refuse** | the gate fires at all |
| `instance-only`, resolved with no count | **allow** | it is not just demanding a number on every thread |
| **untagged**, resolved with no count | **refuse** | the trigger cannot be declined |
| **both tags**, or a `class:` with no name | **refuse, naming the tag** | an unreadable tag is not a third policy |

"Exactly one" in step 1 is an instruction to the reviewer, and an
instruction is not an enforcement — the malformed-tag row is what makes the
vocabulary closed. Both tags together and a malformed `class:` are
**UNMEASURED**, which refuses: a gate that silently picks one of two
conflicting tags, or reads an unparseable one as `instance-only`, hands the
tagger a way to choose the outcome by writing something ambiguous.

Without the `instance-only` row the check cannot distinguish a swept class
from an unswept one — it just requires a number everywhere, which every
author learns to type. Without the untagged row the gate is opt-in by the
party it constrains. A
battery feeding it only class-tagged threads varies one axis while the
defect sits on the other.

What would falsify the whole idea: the counts get written, and the five-or-more
tail on **measured** rounds does not move off 4.4%. The population to watch is
measured rounds, not all rounds — conflating them points this at the half of
the problem these mechanisms cannot reach.

### Cannot be meaningful in this deployment

Four criteria that would measure a constant here. They are not debt, and
leaving them in the remainder overstated it — but each says what would make
it meaningful again, because three of the four turn on headcount and the
fourth turns on a setting, and both can change.

| Criterion | Why it is a constant here | What would make it meaningful |
|---|---|---|
| CRC-M9 — human-time metrics | Approvals per pull request is **0 by configuration**, not by behaviour: branch protection declares no `required_pull_request_reviews`. Median and p95 of a constant are the constant. | Requiring any human approval at all. This is a setting, not headcount — see the blocked row below. |
| CRC-E5 — only trusted authors get the lighter paths | One human, one account. Every author is the trusted author, so the partition has one side. | A second author. |
| CRC-E7 — whoever prompted the change counts as a reviewer | The prompter and the only possible reviewer are the same person, so the rule either waives review entirely or does nothing. | A second person. |
| CRC-F2 — new behaviour ships to internal users first | There is one user, and this repository's only consumer of its own scaffold is itself. "Internal first" and "everyone" name the same set. | A second consumer, or an external one. |

### Blocked on an owner decision, not on engineering

Two criteria are satisfiable by **repository configuration** and cost no
engineering. They are listed apart because "nobody has built it" and
"somebody has to decide" are different debts, and the second does not get
smaller by working on it.

Both are also unobservable from inside this tree for the same reason CRC-C2
is — they are GitHub state, not tree state. Binding either of them needs a
check that reads the API, which is a design decision in its own right.

| Criterion | The setting | What it closes |
|---|---|---|
| CRC-C3 — a false positive clears by closing the thread with a reason | `required_conversation_resolution`, **`true` today and NOT continuously true since 2026-10-23** — applied 2026-10-23, read `true` 2026-10-25, read **`false`** on 2026-11-07, re-applied the same day (#1650). Phase 0 below records the regression, its mechanism, and the three different day-counts this incident has — the setting was off for **at most 11 days** and that is an upper bound rather than a measurement. Separately and earlier, this row read `currently false` until 2026-10-25 and was stale then too. | The native mechanism for "a finding blocks merge until it is dispositioned", which is also half of CRC-B8. **It is in force and, since 2026-10-26, it has something to act on:** the generated workflow's `ai-review-threads` step opens a review thread per finding, and #1614 carries four. This cell read "nothing to act on" until then, and until 2026-11-07 it went on to say the reading was still missing — *no pull request has yet been observed blocked by an unresolved thread with every other required context green*. That sentence was already false when it was written and stayed in the row for twelve days — a count about this row's staleness, not about the setting's outage, which the Phase 0 table below keeps apart: Phase 0's row in *Readings taken* records **four draws** (#1616, #1622, #1627, #1858), each one exactly that observation. The setting's effect is measured, not inferred. What is genuinely missing is a check that would have caught the regression while it was live — `readFindingDisposition` is newer than the incident and has no live history at all. |
| CRC-E8 — an approval covers one specific commit | `required_pull_request_reviews` with `dismiss_stale_reviews`. | Nothing today: with no required reviews there is no approval to carry or dismiss. `gh pr merge --match-head-commit` is a convention agents follow by hand. |

### Contested — this repository gives two opposite instructions

A sixth state, added by #1469, and it is not a shade of the one above.
*Blocked on an owner decision* means nobody has answered yet. **Contested
means the repository has answered twice, in opposite directions, and both
answers are current and deliberate.** An unticked box reads as "not done" in
both cases, and the difference is what an agent does next: a blocked item
waits, and a contested item must not be actioned from either document alone.

That distinction is not bookkeeping. On 2026-10-23 this criterion was read
out of the Phase 0 list above as a setting costing no engineering, and
applied. `PROTECT-1` in `test/scaffold-conformity.test.ts` runs inside the
managed **pre-push hook** and reads the live GitHub API, so it is not a
function of anybody's diff: every session in every worktree was refused the
moment the setting changed, with no commit anywhere to revert. Reverted
about four minutes later; the reading was re-run at 1 pass, 0 fail.

| Criterion | What this spec says | What the tree says | Standing |
|---|---|---|---|
| CRC-F1 — a merge queue re-runs every check against main | Phase 0 names `strict: true` as the cheaper half of a merge queue, costing minutes and no engineering. | `PROTECT-1` (`lib/branch-protection.ts`) **fails on `strict: true`** for a user-owned account, because it serialises every swarm's pull requests — measured at ~2.5 min per PR, 18 open PRs all `BEHIND` and none broken — and merge queues are unavailable on a user-owned repo. | **PROTECT-1 wins.** It is executed on every push by every session; this spec is prose. A rule nothing executes is not a rule, and this one has already been followed into an outage. |

**PROTECT-1 refuses the obvious reverse too, and #1469 removed the reason.**
It declines to *recommend* `strict: false` while any required context does
not run on `push:` to the default branch, because push-CI is then the only
thing catching the semantic conflict — two changes green alone and broken
together. Measured 2026-10-24: `test` and `ai-review` are the required
contexts, and `readPushCi` reported `missing: ["ai-review"]`. #1469 gave the
generated `.github/workflows/ai-review.yml` a `push: branches:` trigger and the same reading
now returns `missing: []`, so the precondition is satisfied and the decision
is unblocked in both directions.

**What that trigger does NOT do, stated here because the tempting reading is
the wrong one.** `ai-review` on a push reviews nothing: the review action
throws `Unsupported event type: push` before it reads anything, exactly as
it does on `merge_group`, so the job annotates UNMEASURED and passes. The
semantic-conflict net PROTECT-1's argument rests on is `test`, which has run
on push since the first scaffold. What changed is that a required context
now REPORTS on push; nothing about main is more reviewed than it was.

So CRC-F1's honest reading is: the *hole* it names is real — with
`strict: false` an armed pull request can merge green against a base it
never ran against — and the remedy it names is one this repository's own
conformity suite refuses. Ticking it would certify a setting the tree
rejects; counting it as remaining engineering would be false too, because
there is nothing to build. The decision is the owner's and the owner now has
both readings. `test/ai-review-push-trigger.test.ts` holds the trigger.

### Deliberately not adopted

| Criterion | Reason in full |
|---|---|
| CRC-M8 — bugs first, rounds second | The deviations table below. The order is inverted here on purpose; the *enforcement* half is unbuilt either way. |

**CRC-N2 left this bucket on 2026-10-24 (#1600).** Its deviation row has been
retired from the table below, because the condition that row named — *"an
adjudicator re-emits unresolved findings"* — fired: the carry step on run
`40137812549` reported `2 finding(s) from earlier rounds are unanswered at
this commit`, a resolved value and not a configuration.

**That evidence was necessary and it was not sufficient, and #1601 is the
reason this paragraph is longer than the sentence above.** Run `40137812549`
proves the carry step emits a number. It does not prove the number is right,
and on 2026-10-24 it was not: the carry compared the recorded anchor against
the recorded LINE NUMBER, so an edit anywhere above a finding re-pointed the
anchor and the finding was classified resolved. Measured live on PR #1597,
where a `high` that was never fixed vanished from rounds 6 and 7 — see
*Measured non-obvious facts* below. **Narrowing the reviewer's scope on top of
that carry would have removed the second chance that was masking it**: under
`scope=full` the reviewer re-reads the branch and can re-find a defect the
carry dropped, and under `scope=diff` a dropped finding in an untouched file
is seen by nothing at all. **That second chance has since been measured and
it is rare** — the drop corpus, the re-raises and how clean they were are
recorded once, in *Measured non-obvious facts*, and deliberately not restated
here. The ordering was right, and the measurement is worth reading before
anyone cites this paragraph as though the cost were large. So the condition
for adopting CRC-N2 is not *the
carry emits findings* but *the carry does not silently drop them*, and the
first was being read as the second. **#1600 therefore ships the content-
addressed anchor first and the narrowing on top of it**, in that order, and
the row below records both.

The criterion is **adopted and still unticked**, and the reason is unchanged
and independent of #1601: what has been built is a scope WORD, and whether
the reviewer confines its reads to it is UNMEASURED.

**The deviations table is not this bucket, and the difference matters.** It
carries a third row, CRC-B8, whose own text says *"This is the defect, not a
deviation."* A criterion listed there under protest is not a decision to
deviate, so CRC-B8 counts with the remainder below and these two do not.

### Not done — the remainder, with what is there instead

**33 bullets, one per criterion that leads one**, listed because the
near-misses are the expensive ones: each has something in the tree that
resembles it and is not it. The unit is stated because this line read `34`
from before CRC-N6 was added until 2026-10-26, when counting it found 29 —
the number had been stale for long enough that nobody could say what it had
counted, and incrementing it would have carried the error forward. One
further id is NAMED inside these bullets without leading one (CRC-A6); it is
accounted for in its own bucket, and one bullet leads with TWO ids
(**CRC-E3, CRC-E9**), which is why 35 ids appear here and 33 is the right
count of this list.

**Every number in the paragraph above is recomputed from the bullets by
`test/code-review-convergence-spec.test.ts`, and that is the fix rather than
the recount.** This sentence drifted three times inside one pull request
(#1619) and every repair was another hand tally — the instrument that
produced the drift. Round 4's reviewer said so as an approach finding and was
right. It had also named CRC-E9 as mentioned-but-not-leading, which it is
not: it co-leads a bullet with CRC-E3, so 29 bullets carry 30 leading ids.
Three quantities live in one sentence — bullets, leading ids, ids mentioned
anywhere — and conflating any two of them is how it moved each time.

**Round 5 then asked the right question about the rest of the document, and
one of its two proposed answers is wrong.** It observed that this file
hand-types dozens of other tallies — *272 (finding, later round) pairs*,
*147 parseable ledgers*, *161 distinct rounds*, *31 review threads of which
12 were one note* — none of them bound by anything, and offered two ways out:
machine-verify them, or declare them exempt. **Machine-verifying them is not
possible and would be wrong if it were.** The classes below are sorted by
where the authority for a number lives, and only the first is a property of
this document.

**Those four figures are citations, not readings taken here**, and round 6
was right that nothing in the sentence said so. Each is stated with its
date, its method and its controls in *Measured non-obvious facts* below —
272 pairs and 147 parseable ledgers under the second-chance reading taken
2026-10-24, 161 distinct rounds under the round-3 floor, 31 review threads
under the fifteen-rounds draw — and is named up here only as an example of
the class. A citation and a fresh reading are the same shape in prose, which
is exactly why the rule below is about where the number is TAKEN.

| Class | Example | Can a test recompute it? | Rule |
|---|---|---|---|
| **Document-derived** | the bullet count, the id set, which criteria sit in which bucket | Yes — it is in the file | **Must be computed.** A hand-typed one is a defect |
| **World-derived** | `15 ai-review runs`, `147 parseable ledgers`, `12 entries and truncated 5` | No | **Must carry its date and the command that took it** |
| **Cited** | Tricorder's 10% probation threshold, GitHub Security Lab's 500 CVEs | No — nothing here can take the reading | **Must name a retrievable primary source.** A figure whose only trace is a secondary summary is not citable and must be dropped, not softened |

A world-derived number re-measured gives a **different** answer, because the
world moved — that is what makes it a measurement rather than a tally. Re-
running `gh run list` against a branch next month and reddening the document
when the count changed would be a check that fires on the truth. So the
obligation on those is not verification but **re-takeability**: state when it
was read and with what, so the next reader can take the reading again and see
for themselves that it moved.

All three drifts this pull request fixed were document-derived, and the one
test now added covers that class where it is concentrated. The world-derived
readings in this file are dated where they are stated and are not, and cannot
be, bound by a test.

**The re-takeability check is BULLET-granular, and that bound is stated
because round 8 of this pull request's review found it and was right.** It
asks whether a bullet stating a measurement declares a date, a run, a commit
or a command. It cannot ask whether *this* marker governs *that* number — so
a figure appended to a bullet that already carries a marker passes. The gap
is not closable by a tighter regex: per-sentence granularity reds correct
prose, because *"33 defects were dropped. 2 were raised again. 31 were never
seen again"* is three sentences governed by one Method clause above them, and
requiring the date in each is noise. Requiring the marker to PRECEDE the
number does not help either, since an appended figure follows it.

So what is enforced is the narrow claim — **every bullet stating a
measurement declares a provenance** — and the remainder is declared rather
than implied. Rounds 4 through 8 each found the same class one layer further
up; a check that implied it had closed the class would have been the next
instance of it.

- **CRC-A1** `missingEvidenceViolations` requires a runnable command per AC and `gates/workflow.test.ts` enforces it — but only inside a harness ship run, and `ship.mode` is `direct`. Dormant on the lane this project ships on.
- **CRC-A2** Nothing makes a fresh-context subagent review the diff before the PR opens. The generated pre-push hook runs conformity tests, not a review.
- **CRC-A3** `scripts/check-instruction-surface.ts` holds `CLAUDE.md` under a byte budget. Nothing checks it states stack, conventions, goals and non-goals.
- **CRC-A4** **Both halves are now instructed, and the instruction has a subject to be measured against — but no reading, so the box stays open.** The second half always held: `REVIEW.md` names "a line that was true of a previous revision and is now false" as a defect class. #1507 adds the first as its own row — *it does what `CLAUDE.md` or an always-loaded `.claude/rules/*.md` says not to do* — with the instruction the row needs to be actionable, which is to quote the sentence being held against the code and name the file it is in. A convention break nobody can quote is an opinion, and the row says so. **The objection to adding it was checked again rather than inherited** (#1507): `CLAUDE.md` is in `AI_REVIEW_UNTRUSTED_PATHS`, and in the generated workflow the step `Restore untrusted paths from the pull request base` precedes `Run the AI review`, `git rm`-ing each name and taking the base's copy — so a branch cannot legalise its own change by editing the conventions it is measured against. `.claude` is in the same set, which is what extends the clause to the rule files. **Why it is still not ticked**: *flags* is behaviour, and the subject has not been run against the live reviewer. `evals/ai-review-control/subjects/worktree-state-write/` is the plant — a compacted copy of the decision half of `lib/project-state-root.ts` whose new arm lets a linked worktree run the project-state generator, which `CLAUDE.md` forbids (#296), beside a `clean` variant byte-identical outside that arm. Its premise is proved in `test/review-negative-control.test.ts` — the convention is read out of `CLAUDE.md` rather than quoted in the manifest, the permission gap is exactly the linked-worktree row, and the two candidates are asserted to agree line for line everywhere else — and that is a property of the SUBJECT, not of the reviewer. **Promotion condition**: N readings of that directory's planted case, scored through the `score` command of `evals/ai-review-control/run.ts`, with N and the full outcome set stated, because the reviewer is a sampled instrument (#1290, CRC-B3) and one `DETECTED` is one draw. Ticking on the plant's existence is ticking on a mechanism, which is what `CRC-A6` exists to avoid. **Until #1511 that condition was not merely unmet but unreachable**, and this note did not say so: the ledger comment is the only durable copy of a review, and #1509 measured that no round entry has ever carried a `verdict` while the writer's projection dropped `failure_scenario`, so every captured round scored `UNMEASURED` and `DETECTED` could not be returned by the `score` command at all. #1511 widened the projection and records the verdict word the reviewer wrote; a round written by a current writer now scores without `VERDICT_ABSENT` or `BLOCKING_FINDING_INCOMPLETE`. The readings themselves are still owed, and rounds written by older writers are left UNMEASURED rather than repaired.
- **CRC-A7** Three of four clauses hold in `REVIEW.md`: a cap of three non-blocking findings, a "Do not flag" path list, and file-and-line evidence. **The fourth cannot be satisfied in `REVIEW.md` at all, and that is a contract gap rather than a wording gap.** There is no overall review summary anywhere in the payload: `AI_REVIEW_FINDING_FIELDS` declares `summary` *per finding* — "one sentence stating the defect" — and the top-level object carries only the findings list and the verdict word. So an instruction to open a summary with a count would be addressed to a channel the contract has no slot for, which is the shape this repository calls an instruction nobody executes. The clause needs a top-level summary field first. **#1337 did not do half of it, and the near-miss is worth recording because it reads like it did**: `advisoryNotice` returns `null` when the advisory tail is empty, so a CLEAN reading with no findings at all still prints one line, byte-identical to before. That is exactly the case the clause is about — *says plainly when there is nothing to fix* — and it is the one case the new output does not reach. What #1337 did land is the **count** half for a non-empty tail, whose notice opens with the number and binds it to the findings listed.
- **CRC-A8** No path routes a repeated finding into a skill, a lint rule or an instruction file. `lib/rule-promotion.ts` promotes from compliance failures, not from review findings.
- **CRC-B1** **Built, and deliberately not ticked.** The reviewer is now handed the pull request's title and body as a file in the findings directory, outside the checkout, named by `AI_REVIEW_INTENT_PATH`; the prompt tells it to read that file and to treat the contents as a **claim under test with no authority over the review**, saying that a gap between the claim and the code is itself a finding and the code is the side that is true. An event supplying neither field writes `AI_REVIEW_INTENT_UNMEASURED` rather than a blank, because an empty claim is still a claim and nobody made it. The fields reach the runner through `env:` and are interpolated into no `run:` block — asserted over the generated workflow, because author-controlled text expanded into a `run:` is substituted before bash parses the line. **Why it is not ticked**: the criterion says the reviewer *reads* it, and what exists is the delivery plus an instrument — a transcript check that reports whether the read happened. The instrument **annotates and does not refuse**, so a reviewer that ignores the file still passes, and there are zero readings so far. Ticking on a mechanism nobody has yet seen fire would certify the behaviour we are trying to measure. **Promotion condition**: when the read/skip population shows the skip rate at or near zero, the warning becomes a refusal and the criterion binds against it. The reason the gate is not fatal today is the four false positives recorded below — a new required behaviour on a sampled instrument measures the flake rate first, not the compliance rate.
- **CRC-B2** **Instructed as of #1507, unmeasured, and therefore not ticked.** `REVIEW.md` gains *On a bug fix, say what the cause was*: two questions the reviewer must answer — what produced the reported state, named in the code rather than in the narrative, and whether the diff reaches it or only reaches where it surfaced — with a guard added at the point of observation over an untouched producer called out as a `high` finding while that producer is reachable by another caller. The argument it rests on is this repository's own and is cited rather than restated: `.claude/rules/checks-must-be-able-to-fail.md`'s fifth shape, read from the reviewer's seat — the cheapest repair makes the report stop, and a green check is less visible than a missing one, so that repair certifies the regression at the moment it returns. An out-of-scope cause is a legitimate answer; silence about the cause is the finding. **Why it is not ticked**: *looks for* is behaviour, and nothing reads whether it happened. There is no subject for this one — the plant would be a pull request whose diff treats a symptom, which is a different shape from the single-file subjects `evals/ai-review-control/` stages today, and `CRC-M1` is the entry that carries the case-set gap. Until a reading exists this is an instruction with no compliance reading, which is what `CRC-A6` names.
- **CRC-B3** One reviewer agent per round. **Not adoptable before CRC-B4, and the criterion now says why**: N generators over a sampled instrument are N draws, and run `39962683401` is a same-tree pair that disagreed BLOCKED/CLEAN with a false positive on the blocking side. Without a quorum to filter them, parallel generation multiplies exactly that. Ordering, not absence of effort.
- **CRC-B4** **Half, and the half that is missing is the one the criterion is named for.** Before #1476 this read "nothing deployed takes a vote", and that was accurate: `lib/finding-jury.ts` held the group size, the quorum, per-verifier votes and a disagreement flag, and `arbitrate` — the only path reading them — had no caller outside `lib/`, `test/` and `scripts/arbitrate-finding.ts`. #1476 adds `lib/ai-review-jury.ts`, which the deployed adjudicator wrapper injects: it is handed only the findings that would otherwise **BLOCK**, reads a ballot directory with one file per verifier, and writes **every verifier's individual vote, the agreement count and the disagreement flag** to the finding ledger at decision time, with a `null` reading and a named refusal for a group that could not be convened. **A finding the group votes down still blocks.** The vote is recorded and subtracts nothing — `JG-6b` asserts the adjudicator's exit code and first line are byte-identical with and without a ballot — so the clause *"surfaced only if enough agree it is real"* is **not satisfied**, and it is not satisfied by choice rather than by omission. Two prerequisites, both structural and neither a wording change: **(1) real independence.** `AI_REVIEW_DENY_RULES` denies `Task` and `AI_REVIEW_ALLOWED_TOOLS` is `[Read, Grep, Glob, Write]`, so one review-action invocation cannot convene three verifiers — a ballot it wrote is a quorum of one wearing `VERIFIER_GROUP_SIZE` names, which is this criterion's own named counterfeit arriving by a different route than the constant `agree`. It needs `VERIFIER_GROUP_SIZE` separate action invocations, each with its **own** writable directory; the single findings directory will not do, because widening `AI_REVIEW_WORKSPACE_WRITE_DENY` is documented at the constant as the cheapest wrong fix. **(2) a base-ref read.** The review runs on the head checkout, so a ballot able to demote a finding is a gate whose input the branch under review can write. Until both land, a quorum that subtracts is a worse instrument than no quorum. What the ledger rows buy meanwhile is the population CRC-B6 needs: votes recorded against real findings, under the real severity split, with the demotion switched off — so the A/B is computable later without re-running the sample. **A third prerequisite was added 2026-10-27 and it reorders the other two: the deciding half must not be built as three model verifiers.** *What the published measurements say about a verifier group*, below, records the readings — at matched spend a group of same-model instances is the design the literature measures losing, and a second pass given no evidence the generator lacked is measured **degrading** rather than filtering. The filtering work is done by handing the verifier something mechanical the generator never had, not by adding instances. So the deciding half is now specified as **a mechanical pre-check first, then a small independent ballot with an adaptive stop** — a smaller build than the one this criterion carried. **The pre-check is the part the evidence supports; the group size is a budget floor and the section says so.** An earlier draft of this sentence sized the group from the cascade-depth reading and was withdrawn on review, because that reading measures sequential dependent routing and our ballot is deliberately the independent kind — nothing cited here measures a two-sample independent ballot at all. The independence prerequisite above survives unchanged and is the reason: it is what keeps the ballot in the self-consistency shape rather than the debate shape.
- **CRC-B6** `compareReviewOutcomes` and `evals/ai-review-control/variance-capture.ts` exist. No filter has been A/B tested before being kept, and the variance control reads zero by construction — see below.
- **CRC-B8** Half, and a different half since #1337. The advisory tail is no longer discarded — `advisoryNotice` names every counted non-blocking finding, with a key, in an annotation that says each is UNANSWERED. What is still missing is the requirement: nothing obliges anyone to answer one, so "fixed, or resolved with a stated reason" remains a request. A duplicate or a dropped-category filing is refused at the chokepoint; ALLOW is still the default for a novel finding.
- **CRC-B9** No per-repo review depth. `ceremonyTier` LIGHT / STANDARD / THOROUGH is the harness gate ceremony, a different axis.
- **CRC-E3, CRC-E9** `lib/risk-tier.ts` now exists, so these two have something to second-guess and something to loosen — which is why they were sequenced after #1437 rather than built with it. `E3` needs a second classifier that can raise a LOW the first one is content with; `E9` needs a recorded outcome per tier to loosen against, and the ledger does not carry a tier yet. `LOW_MAX_FILES` and `LOW_MAX_LINES` are therefore declared strict and not evidence-based, and that is stated at the constants rather than left to be discovered.
- **CRC-E6** Branch protection declares no required reviews, so no approval counts toward anything and the criterion is vacuous rather than satisfied.
- **CRC-F3** No one-step rollback, and none exercised.
- **CRC-F4** No incident review asks which layer should have caught it.
- **CRC-F5** No circuit breaker. The source admits this as a gap on their side too.
- **CRC-M1** Two subject directories since #1507, holding two authored plants of different kinds — a behavioural defect and a convention break — and three clean variants. Still not a case set drawn from past incident-causing pull requests, and every subject is a single file, so a criterion whose defect is a property of a whole pull request (`CRC-B2`'s symptom-only fix) has no shape to be staged in.
- **CRC-M3** Nothing adds a case when an incident happens.
- **CRC-M4** Nothing rescores the whole set when the reviewer's prompt, tools or model change.
- **CRC-M5** No schedule runs the eval. The only crons in the tree are `.github/workflows/issue-audit.yml` daily and `.github/workflows/action-pins.yml` weekly.
- **CRC-M6** One bucket of four is derived from evidence. The other three report UNMEASURED unless hand-declared, and `noiseRate` is `null`.
- **CRC-M7** The control exists and counts `FIRED` on clean subjects. The criterion's own number — findings that *would have led to a harmful change* — is declared UNMEASURED by the control's README, because a finding carries no remedy anything can apply. A tripwire in `test/review-negative-control.test.ts` reds the day the contract grows one.
- **CRC-M10** Nothing tracks revert or incident rates.
- **CRC-M12** One bucket, not three. `lib/review-execution-reading.ts` already distinguishes `EXECUTION_FILE_ABSENT`, `NO_TOOL_CALLS`, `NO_REVIEW_POSTED`, `REVIEW_COUNT_UNAVAILABLE` and `DIFF_TRUNCATED` as reason codes, and `record-ai-review-unmeasured` (#1488) records a kind per round — but `no_payload`, the nothing-posted case and `DIFF_TRUNCATED` are not named failure modes in this spec, so nothing binds the recorded kinds to a criterion and the rate they roll up into is a single undifferentiated 45.8% — read 2026-10-28 with `bun evals/ai-review-control/run.ts rounds` over #1573–#1634, 48 pull requests and 203 rounds, the denominator being ROUNDS.
- **CRC-M13** The census is computed and unreachable where it matters. `toolCallsByName` and `NO_TOOL_CALLS` are wired into the advisory reviewer only (`.github/workflows/claude-review.yml`). The required reviewer is generated and runs in consumer repositories through `bunx rungate@<pin>`, which ships no `scripts/` directory, so there is no command for it to call. Nothing anywhere reports whether a no-payload round read a single file.
- **CRC-M14** No reading names its published version. CI pins `bunx rungate@<pin>`, so a merged `lib/` change is dormant until a release while a merged generated workflow is live on merge — two different latencies behind one number, and the stored readings record neither.
- **CRC-M15** `lib/distribution-standing.ts` checks `standing.published` — the version a consumer can install — for membership in `[registry.latest, registry.previous]`, so one release of lag is permitted unconditionally, and checks `standing.tree` against `package.json`'s version only. Neither reads the published artefact. A tarball whose version is acceptable and whose contents differ from the tree passes, which is how an earlier increment stayed dormant behind a green check. Two earlier drafts of this bullet were wrong about which field is compared to what — the first said SIZE, the second named a field (`standing.taken`) the module does not have — both corrected on 2026-10-28 after the module was read, in review rounds 5 and 6. #1226 is adjacent and unassigned.
- **CRC-N4** **Half of it shipped in #1381 and the half the criterion is named for did not.** The walker exists: the generated `ai-review-carry` step reads the ledger, searches each prior finding's file for the recorded anchor TEXT at this commit (#1601 — it compared the text at the recorded LINE NUMBER until 2026-10-24, and an edit anywhere above a finding dropped it as resolved), and hands the reviewer the unresolved set under one of three readings that may not collapse — `AI_REVIEW_CARRY_READ`, `AI_REVIEW_CARRY_ABSENT`, `AI_REVIEW_CARRY_UNMEASURED`. It restates `readLedger → priorFindings → carryForward` in bash and is bound to the library over one matrix by `test/ai-review-carry-forward.test.ts`, because `lib/scaffold/ai-review-step.ts` may not import: the step is deliberately import-free so that the 27 suites copying it into a temp directory can build mutants that load. What remained was **suppression**, and #1586 built it: `lib/ai-review-suppression.ts` turns the carry step's state file and a ledger snapshot into the prior key set, and `scripts/ai-review-findings.ts` hands the adjudicator a gate over it. Three things keep this criterion unticked. **It is dormant** — the generated job runs `bunx rungate@<pinned>`, so this reaches CI only when the pin moves, and a tick is read as *running*. **It is advisory-only by declared deviation** — a blocking repeat is re-reported and still blocks; see the deviations table. **The key symmetry is new** — before #1586 the adjudicator formed `n:<line>` keys and the ledger held `t:<text>` keys, so a dedupe built on it would have matched nothing while reporting cleanly; `lineTextFor` reads the checkout and `test/ai-review-suppression.test.ts` AS-5 is the control that holds it.
- **CRC-N5** Nothing runs review agents nightly over existing code.
- **CRC-N6** **Named because it was measured, with nothing built.** Five consecutive rounds on #1614 re-raised one already-fixed defect: four consecutive rounds from a docblock that QUOTED the removed regex, and the FINAL round — after the quotation was deleted — from the PARAPHRASE that replaced it, reconstructing a regex literal that appears nowhere in the tree. CRC-N4's dedupe cannot absorb it, because the suppression key is `file \0 line-text \0 summary` and a regenerated finding carries a new summary: it is not a repeat, it is a new finding about code that does not exist. The near-miss is *"do not quote dead code in comments"*, which was applied and then defeated. The reading is in *Measured non-obvious facts*. **It is deliberately NOT a request for new machinery** — the prior-art section above found that a verification gate re-checking each finding against the real code at the cited line is the documented mitigation for the wider class it belongs to, and that gate is CRC-B4. This criterion names the case so a verifier can be held to it; it does not ask for a second mechanism beside one already planned.
- **CRC-H2** Risky code requires a human. There is no `CODEOWNERS` and no required approval, so nothing does.

### Shipped since this audit was taken

A criterion the audit counted as remaining and that no longer is. Kept as a
section rather than deleted: the analysis is the record of what the item cost
and why the shape it shipped in is the right one, and the six states above are
states of an UNTICKED box, so a ticked one belongs in none of them.

- **CRC-B7** — **shipped in #1587**, and the analysis below is kept as the record of what it cost rather than as a statement about the tree. What changed: `Severity` and `SEVERITY_RANK` are now declared in `lib/scaffold/ai-review-step.ts`, the contract module the deployed reader already imports and the only one the mutation batteries can carry, and `lib/finding-jury.ts` re-exports them — **one declaration, no third vocabulary**. `AI_REVIEW_SEVERITIES` was NOT merged into it, because the two must disagree for both to be right: a `critical` naming a file the pull request does not touch blocks under the severity table (magnitude is a property of the defect) and tags `Pre-existing` under this one (attribution is a property of the diff), and folding them would require the reviewer to write `Pre-existing` itself when it is deliberately never given the file list. `findingPathScope` is the single binding both the demotion and the tag read, `tagOrder` is the single comparator, and the tag is applied to the advisory tail as well as the blocking set — the demotion never looked at an `info`, and an `info` about code on `main` is misattributed exactly as badly as a `critical` is. Three clauses, and they have three different costs — reading it as one item is what made it look cheap. **Sorting** is now possible and was not before #1337: there is a rendered tail to put in an order, and `advisoryNotice` and `renderCountedFindings` both emit in payload order, which is whatever order the model wrote. **The vocabulary** does not exist in the deployed path: `SEVERITY_RANK` tags Important / Nit / Pre-existing in `lib/finding-jury.ts`, which the CI path never calls — its callers are `scripts/arbitrate-finding.ts`, `lib/issue-filing-gate.ts`, `lib/finding-arbiter.ts` and `lib/ai-review-jury.ts`; this list read `lib/failure-intake.ts` and `hooks/VerifyPhaseLock.hook.ts` until #1587 measured it, and NEITHER of those imports the module, directly or transitively (found by this repository's own reviewer on #1590) — while the deployed table, `AI_REVIEW_SEVERITIES`, declares `critical`, `high`, `medium`, `low` and `info`. **Pre-existing** is not decidable there at all: `severityOf` decides it from the pull request's changed files and the findings step has no changed-path list to scope against. **The prerequisite is #1204/#1354, not #1337**, because that is the change carrying the changed-path list into this module; until it lands the criterion cannot be ticked on the first two clauses alone. A weaker route to the third exists and is worth knowing before anyone plumbs the diff: `advisoryKey` (named `findingKey` before #1398) identifies a finding by file and summary rather than by line, so the same observation has one identity across rounds and *first seen on round 1* becomes decidable from the accumulated ledger with no diff at all. That is a different and smaller claim than `severityOf`'s — first-seen-round, not present-before-the-pull-request — and it should be labelled as the one it is rather than sold as `Pre-existing`. **One trap for whoever sorts**: `renderFinding` prints `finding <index>`, and the blocking annotation and the advisory notice now share that numbering, so a sort must reorder the display and keep the payload index in the label. A case in `test/ai-review-advisory-findings.test.ts` asserts the tail is indexed against the whole payload and reds on renumbering.

## The order to build the remainder in

Written 2026-10-23 because the work had been running without one, and
criteria were being picked by whichever looked tractable. That produces the
failure this section exists to stop: an agent spends a session discovering
that the criterion it chose is blocked behind one nobody has scheduled, and
writes the discovery down instead of the code.

**The backlog is 30, not 47.** Of the unticked boxes, 8 are mechanisms this
tree cannot observe, 4 cannot be meaningful in this deployment, 2 are
declared deviations, and 3 are repository settings. Only the remainder is
engineering, and the four categories above are not a smaller version of it —
they are a different kind of fact, and the tables above say which is which.

Phases are ordered by **effect on rounds-to-pass**, which the table in *Where
we actually stand, measured* read as 2.64 against the source's 1.32 when this
ordering was set, and **4.19 on 2026-10-27**. Within a phase the criteria are
independent and may be built in parallel. Across phases they are not: each
phase names what the next one needs.

**The ordering is by effect on rounds-to-pass and no phase is pointed at the
largest contributor to it.** That was true when the phases were written and
it is stated under *The re-take, 2026-10-27*; it is repeated here because
this is the paragraph that explains the order, and an order whose own stated
criterion is unserved should say so where the order is given rather than
only where the measurement is.

### Phase 0 — three settings, no engineering

**CRC-C3 was applied on 2026-10-23, SILENTLY REGRESSED, and was re-applied
and bound on 2026-11-07 (#1650).** `required_conversation_resolution` was set
`true` on `main` through a full `PUT` that preserved the two required
contexts, `enforce_admins`, and every other field unchanged.

**And then something turned it off, and this document went on saying it was
applied.** Read from the API on 2026-11-07 it was `false`, and PR #1857 merged
that morning carrying five unresolved review threads, two of them not even
outdated — which the first three draws recorded in the Phase 0 exit table
below say was impossible on 2026-10-27, when one unresolved thread held a pull
request at `BLOCKED` with every required check green.

**Three different day-counts belong to this incident and they measure three
different things.** They are spelled out because an earlier draft stated two
of them in adjacent sentences as though they were one quantity, and the review
of that draft caught it.

| days | from → to | what it measures |
|---|---|---|
| **at most 11** | some time after 2026-10-27 → 2026-11-07 | how long the setting was **off**. An upper bound, not a measurement: the last draw confirms it working on 2026-10-27 and the API read finds it off on 2026-11-07, and nothing narrows the gap because the endpoint emits no audit event. |
| 13 | 2026-10-25 → 2026-11-07 | how long **this document asserted a field nothing had re-read**. 2026-10-25 is the last direct read of `true`; the three October draws exercise the *effect* and are not reads of the field. |
| 12 | 2026-10-26 → 2026-11-07 | how long the CRC-C3 row above went on saying *no pull request has yet been observed blocked* after the first draw made that false. A property of the row, not of the setting. |

**The
fourth draw, in that same table, is #1858 on 2026-11-07** and it is this
paragraph's closing half: it is the only reading taken after the setting was
restored, so it says the mechanism works *now* rather than that it worked in
October, and a restored setting nobody has watched work is a setting on the
same footing as the one that went off. The
mechanism needs no culprit: the protection endpoint's `PUT` **replaces the
whole object**, so any later update that omits this field disables it and
returns 200. There is no event to notice and no error to read.

The sentence this paragraph replaced is the reason it went unnoticed: *"it
stays unticked because the setting is GitHub state and no check in this tree
reads it."* That was an accurate description of a gap and it was filed as a
distinction worth keeping. A setting nothing re-reads is not applied; it is
applied **until something changes it**, and the difference is invisible
exactly when it matters.

**So the fix is a reader, not a better sentence.** `PROTECT-2` in
`lib/conformity.ts` reads the live field through the same probe `PROTECT-1`
uses and FAILS when a tree that opens a review thread per finding does not
require those threads to be answered. The classification is
`readFindingDisposition` in `lib/branch-protection.ts`; a tree that produces
no threads passes and says so, because demanding the setting there would be
advice that changes nothing.

It stays **unticked** all the same. `PROTECT-2` binds the half that says *a
finding nobody answered blocks the merge*; CRC-C3's own sentence is about
**clearing** one, and that half is now a written procedure
(`reference/clearing-a-false-positive.md`) rather than an executed check. A
procedure a person follows is not a test, and ticking it on the strength of
the other half is the move this criterion has already been burned by.

**CRC-E8 does not belong in this phase and is moved to the table above it.**
With one account and `enforce_admins: true`, requiring an approving review
deadlocks the repository: the only possible approver is the author, so
nothing merges at all, including every agent's pull request. That is the
same "needs a second person" constraint CRC-E5 and CRC-E7 carry, and it is a
hard stop rather than a cost. It was listed here in the plan's first draft
and that was wrong.

So Phase 0 is **one setting applied, one CONTESTED, one withdrawn**:

CRC-F1 (`strict: true`), CRC-C3 (`required_conversation_resolution`), CRC-E8
(`required_pull_request_reviews` with `dismiss_stale_reviews`). Minutes, by
the owner. They are first because two further criteria — CRC-E6 and CRC-M9 —
are **vacuous rather than unbuilt** until they land: there is no approval to
count, so nothing can be built that counts one.

**DO NOT ACT ON CRC-F1 FROM THIS LIST. Read its row in *Contested* above
first (#1469).** `PROTECT-1` in `test/scaffold-conformity.test.ts` fails on
`strict: true` by design, it runs inside the managed pre-push hook, and it
reads the live GitHub API rather than the diff — so setting it refuses every
session's push in every worktree, repo-wide, with no commit anywhere to
revert. That is not a prediction: it happened on 2026-10-23, read out of
this paragraph in its previous form, and was reverted about four minutes
later. The paragraph said "minutes, by the owner" and it was right about the
duration and wrong about everything else.

The cost argument below is the one this plan originally made, and it stands
as a cost argument. It is not the binding objection; the binding objection
is a check in this tree that refuses the setting outright.

**If the setting is flipped anyway, the trigger is a number, not a judgement
call: open pull requests ≤ 2, with no agent mid-push.** Under `strict`,
every merge stales every other open pull request, and the repair is
`gh pr update-branch`, which **force-rewrites the contributor's branch** —
including one an agent is pushing to. On 2026-10-23 this repository merged
eleven pull requests with four sessions running; flipping it in that state
converts each merge into five forced rewrites. The hole it closes is real
(an armed PR merging green against a base it never ran against) and it is
not urgent enough to pay that. If it is ever flipped, watch rounds-to-pass:
if `strict` costs more rounds than the stale-base hole does, that is
measurable and the criterion should say so.

**The other direction is now open, which is what #1469 changed.** PROTECT-1
also refused to *recommend* `strict: false` while a required context was
absent from `push:` to the default branch. `ai-review` was that context;
it now carries the trigger, `readPushCi` reports nothing missing, and the
`strict: false` recommendation is available for the first time. The trigger
is not itself a review of main — see the Contested row.

### Phase 1 — stop the repeats

**The tail is the problem, not the median.** 20.5% of pull requests take five
rounds or more, against their 8.9% before; the mean is only a quarter above
theirs. A minority of PRs is absorbing the loop, and a finding re-posted
every round is, arithmetically, an extra round.

| | Depends on |
|---|---|
| **CRC-N4** — no repeats | **a release.** #1586 gave the dedupe its production caller — `lib/ai-review-suppression.ts`, bound in `scripts/ai-review-findings.ts` — so the machinery is no longer uncalled in the source. It is still uncalled in CI: the generated job runs `bunx rungate@<pinned>`, so `lib/` and `scripts/` changes are dormant until the pin moves. The checkbox stays unticked until then, because a tick is read as *running* and the merge does not earn it. |
| **CRC-B7** — Pre-existing tagging | *(cleared, #1587)* #1204 closed, #1354 merged and 0.8.3 shipped, so the changed-file list reaches the adjudicator |
| **CRC-N3** — flag the class, not the line | **a denominator, not a mechanism.** `REVIEW.md` already asks for the class and #1614's round 12 is a real instance of the reviewer giving one. What is missing is a rate: one instance is not a reading. It is in this phase rather than Phase 3 because the cost it removes is the repeat — the author fixing one instance of a class while its siblings sit in the same file — which is what *The author-side half of CRC-N3 is unowned* below says nothing owns |
| **CRC-N2** — diff-only re-review | *(no longer a deviation, #1600)* **an observation, not a merge and not a release.** The decision is in the generated `.github/workflows/ai-review.yml` rather than in `lib/`, so unlike CRC-N4 it is live the moment the workflow lands — no pin has to move. **The same sentence is why #1601's anchor fix is not on this list**: it is a change to the same generated bash, so it lands with the narrowing rather than after it, and the ordering concern — narrowing on top of a carry that drops findings — does not survive the merge. The library halves in `lib/ai-review-rounds.ts` ARE dormant until the pin moves; they are the binding the generated step is held to, not the decider CI runs. What this criterion is waiting for is the reading in *Measured non-obvious facts* below: a real narrowed round on which the reviewer's reads can be shown to have been confined. Until then the scope is a request, and the checkbox stays unticked because a tick is read as *working*. |

CRC-N4 is the single highest-value item in this document and it is not a
design problem. Its own entry says the gap is structural: the only non-test
file naming the module mentions it in prose.

### Phase 2 — stop the false findings

The other half of the tail. A false blocking finding costs a remedy commit, a
CI round and a review round, and run `39962683401` is the measured instance —
a same-tree pair that disagreed BLOCKED/CLEAN with the false positive on the
blocking side.

| | Depends on |
|---|---|
| **CRC-B4** — verifier quorum | the *recording* half is deployed (#1476): per-verifier votes and the disagreement flag reach the ledger for every blocking finding. The *deciding* half depends on `VERIFIER_GROUP_SIZE` separate review-action invocations with per-verifier writable directories, and on reading the base ref rather than the head checkout |
| **CRC-B6** — A/B the filters | CRC-B4's recorded votes — which now accumulate — and a variance control that does not read zero by construction |
| **CRC-B3** — parallel generation | CRC-B4, strictly. Without a quorum, N generators are N chances to block falsely, which is **worse than one** |
| **CRC-N6** — a fixed defect stays fixed | nothing in Phase 1 or 2 — it is independent and small. It is here rather than in Phase 1 because a finding re-raised from text that merely *describes* the removed code is a **false** finding, not a duplicated true one, and the two have different fixes: dedupe cannot help, because the second raise has a different anchor |

### Phase 3 — what the reviewer is told

> **Reordered for one objective.** For the swarm track declared below, Phase 4
> runs before this phase. The reason and its limits are in *The swarm track*;
> for the rounds-to-pass objective this phase stays third.

Cheap, mostly prompt and `REVIEW.md` text, and independent of Phases 1 and 2.
Sequenced third rather than first because a reviewer given more context and
no falsification step produces more confident false premises — so Phase 2
earns the right to do this one.

CRC-A4 (flag a `CLAUDE.md` convention break — the obvious objection does not
apply, see its entry), CRC-B2 (root cause on a bug fix), CRC-B9 (per-repo
Quick/Standard/Deep), CRC-A7 (the summary clause), CRC-B1 (the diff read
against the whole repo **and the PR's stated intent** — the intent half is
text the reviewer is handed, which is what this phase is).

**#1507 did the text half of CRC-A4 and CRC-B2 and ticked neither.** Both
clauses are in `REVIEW.md` and CRC-A4 now has a planted subject to be
measured against. What is missing in both cases is a reading of the live
reviewer, and what remains of this phase is CRC-B9 and CRC-A7, which need the
file this phase's other two did not: see each entry for why.

### Phase 4 — findings get answered, and repeats get fixed at the source

> **Reordered for one objective.** For the swarm track declared below this
> phase runs before Phase 3, and only **CRC-B8** of it is the swarm's need —
> CRC-A2 is unrelated. See *The swarm track*.

CRC-B8 (every finding answered — CRC-C3 from Phase 0 is half of it), CRC-A8
(a repeated finding becomes a rule or a lint, not another finding), CRC-A2
(a fresh-context review before the PR opens), CRC-A1, CRC-A3.

### Phase 5 — the instruments

CRC-M6 (four outcome buckets; one of four is evidence-derived today),
CRC-M10 (revert and incident rates), CRC-M1/M3/M4/M5 (an incident case set
and a daily rescore), CRC-M7 (a finding carries no remedy, so the control's
own number is UNMEASURED), CRC-E3 and CRC-E9 (a second classifier, and a
ledger that carries a tier to loosen against).

**Five more belong here and were unplaced until 2026-10-28.** CRC-M2 (the
case set's cases are expert-confirmed — a human act, but one this repository
can perform, unlike the approval criteria below), and the four readability
criteria the reviewer itself cannot report on today: CRC-M12 (an unreadable round names its mode),
CRC-M13 (whether the reviewer READ anything, recorded apart from whether it
found anything), CRC-M14 (every reading names the published version it was
taken under) and **CRC-M11**, which is ticked and **contradicted by #1592** —
the counter counts run ATTEMPTS where the sentence says ROUNDS, so the tick
records a binding and not a trustworthy number.

### Phase 6 — release and detection

CRC-F3, CRC-F4, CRC-F5, CRC-N5, CRC-H2. Last because none of them moves
rounds-to-pass, and CRC-F5 is a gap the source admits on its own side.

**Four more join them, by that same test.** CRC-F2 (new behaviour ships
behind a flag, internal users first) and CRC-M15 (the staleness check reads
contents, not a version string) are release mechanics on their face.
CRC-C1 and CRC-C2 are here for a less obvious reason and it is worth
stating: their remaining work is **one piece** — bringing the security pass
into repo CI — and it moves rounds-to-pass not at all. CRC-C2's
bug-review half already holds (`test` and `ai-review` are required contexts
with `enforce_admins` on, and `required_conversation_resolution` is `true`);
what is missing is a security check to require, which is CRC-C1. Placing
them earlier would order the plan by how important security sounds rather
than by the criterion this plan's order actually uses.

### Phase placement — every criterion has exactly one home

Added 2026-10-28, because the phase sections above name some criteria and
not others, and a criterion in no phase is unreadable as anything: *nobody
has reached it*, *it cannot start*, and *it is finished* all render as
absence, and the backlog is built from this document.

**The count that prompted this, and the instrument that got it wrong twice.**
Against `ccd62c7b`, a word-boundary scan of every id over the phase span
(`### Phase 0` to `### Exit conditions`) reported **33 of 61** placed. Both
halves of that reading were false and they nearly cancelled: it counted
CRC-E5, CRC-E6, CRC-E7 and CRC-M9 as placed because Phase 0's prose *names*
them while placing none of them — a citation, not a claim — and it missed
CRC-M3, CRC-M4 and CRC-M5 because Phase 5 writes the four of them as one
slash-joined run headed by CRC-M1, in which the last three ids never appear
whole and no word-boundary match can see them. The true figure was **32 placed, 29
unplaced**. A detector whose two errors point in opposite directions returns
a believable number, which is why the table below is a declaring position
with a test over it rather than another scan of the prose.

Three of the values below are not phases, and that is deliberate. Forcing
*"needs a second person"* or *"nothing here can observe it"* into a numbered
phase would state a plan for work that cannot start, which is the failure
CRC-E8's withdrawal from Phase 0 already records once.

| Placement | Criteria | What the value means |
|---|---|---|
| **Phase 0** | CRC-C3, CRC-E8, CRC-F1 | settings, no engineering — and two of the three do not survive contact: E8 is withdrawn, F1 is contested |
| **Phase 1** | CRC-B7, CRC-N2, CRC-N3, CRC-N4 | stop the repeats |
| **Phase 2** | CRC-B3, CRC-B4, CRC-B6, CRC-N6 | stop the false findings |
| **Phase 3** | CRC-A4, CRC-A7, CRC-B1, CRC-B2, CRC-B9 | what the reviewer is told |
| **Phase 4** | CRC-A1, CRC-A2, CRC-A3, CRC-A8, CRC-B8 | findings get answered, repeats fixed at the source |
| **Phase 5** | CRC-E3, CRC-E9, CRC-M1, CRC-M2, CRC-M3, CRC-M4, CRC-M5, CRC-M6, CRC-M7, CRC-M10, CRC-M11, CRC-M12, CRC-M13, CRC-M14 | the instruments |
| **Phase 6** | CRC-C1, CRC-C2, CRC-F2, CRC-F3, CRC-F4, CRC-F5, CRC-H2, CRC-M15, CRC-N5 | release and detection — nothing here moves rounds-to-pass |
| **Done** | CRC-A5, CRC-A6, CRC-B5, CRC-C4, CRC-E1, CRC-E2, CRC-E4, CRC-N1 | ticked and bound. Not *no work ever again* — CRC-B7 and CRC-M11 are also ticked and are **not** here, because an open issue contradicts each |
| **Blocked — needs a second person** | CRC-E5, CRC-E6, CRC-E7, CRC-M9 | one account plus `enforce_admins: true` means an approval cannot exist, so E6 and M9 are **vacuous rather than unbuilt** — there is nothing to count. The blocker is CRC-E8's withdrawal and it is named in Phase 0 |
| **Not observable here** | CRC-H1, CRC-H3, CRC-H4, CRC-H5 | statements about human judgement. *A mechanism exists; this repository cannot observe it* above says why: nothing distinguishes them being honoured from them being ignored |
| **Not adopted — deliberate** | CRC-M8 | *Deliberately not adopted* above holds exactly this one. Its order is inverted **on purpose** — `MISSED` and `FIRED` are weighted equally because nobody absorbs the noise here — and the deviations table gives the revisit condition: *a human is reading the findings again, or the cost of a false block falls*. **The first draft of this table put it in Phase 5**, which read as *pending work, blocked on the instruments*, and invented a second revisit condition the document does not hold. That is the two-spellings failure arriving inside the table built to end it; the reviewer caught it on #1647 |

**This table is the placement, and the phase sections above are its
reasons.** Two spellings of one fact drift apart — this document says so
about measurements and it is just as true of a list — so when they disagree,
this table is wrong until it is fixed, not the other way round, and
`test/code-review-convergence-spec.test.ts` refuses any criterion that is
missing from it, listed twice, or listed under a value not in the first
column above.

**What it does NOT do is create 29 issues.** A placement is a label on work
that already exists or is yet to be scoped; filing an issue per criterion
would put this project at the three-to-one opened-against-closed ratio that
rule 7 of `AGENTS.md` exists to prevent. The tracker gets an issue when
somebody is about to do the work.

### Exit conditions — what must be OBSERVED before the next phase starts

Added 2026-10-26. The phases above order the work and say what each one needs
from the last. They do not say when one is **done**, and without that the
honest reading of progress is a checkbox count — which is the wrong
instrument twice over.

**A tick means a criterion is bound, not that the phase moved the number.**
`scripts/sync-sc-status.ts` ticks a box when a test names the id, and
`.claude/rules/claiming-sc-coverage.md` is deliberate about that being a
declaration of intent. So a phase can reach 100% ticked while rounds-to-pass
sits where it was: every mechanism present, bound, and not yet making a
difference to the thing this document exists to move.

So each phase below exits on an **observation taken on a real pull request**,
not on a count and not on a unit test. One per phase, falsifiable, and
stated so a reader can be wrong about it — which is the lesson *The thing
that would make this plan wrong* records below, where a precondition that
read "the fix has merged" was checkable and was the wrong thing to check.

**Every row below states a negative control**, because the first draft of
this table did not and an audit found six rows satisfiable by something that
never happened. Each row therefore names the state that must NOT read as a
pass. A row without one is the defect this section exists to prevent,
arriving inside the section.

| Phase | Exits when this is observed | The state that must NOT read as a pass |
|---|---|---|
| **0** settings | Every OTHER required context is green — `test` and `ai-review` both `SUCCESS` — and the pull request is still held, then goes mergeable when **only** the thread is resolved | `BLOCKED` while any other required check is failing or pending. That reading is **overdetermined** and attributes nothing. See the swarm track below, where this spec made exactly that error |
| **1** stop the repeats | Round two posts **at least one NEW thread** for a different finding, **and zero** for the finding already threaded on round one | round two posting **nothing at all** — which an absent payload, a fork's read-only token or CRC-N2's narrowing all produce. Zero threads is not a deduplication, and without the new thread there is no proof the poster was even live |
| **1** (the number) | On **measured rounds only**: five-or-more below **4.4%** and mean-to-pass below **1.58** | using the ALL-rounds figures (20.0%, 2.65). Those are dominated by the rounds that produce no review, which Phase 1 does not touch — the spec says conflating the units "points the whole plan at the smaller half of its own problem". **And reading the row above as though it had satisfied this one.** They are two exit conditions and only the first has been observed: measured-only stood at **25.8% and 3.03** on 2026-10-27, against thresholds of 4.4% and 1.58, so this row is **UNMET and has moved away from its target**. **The thresholds themselves are now suspect and this row is the reason that matters.** Both were set from the 2026-10-24 measured-only column, which the 2026-10-27 re-take found was built by scoring a never-reviewed pull request as a one-round pass; the 10-27 figures above are built by refusing those pull requests instead, so the two sides of this comparison use different arithmetic and the gap is not a measured distance. The verdict does not turn on it — UNMET holds on either rule, and the first draft of this cell said 18.6% and 2.19 under the wrong one — but **the thresholds need re-deriving before this row can state a distance rather than a direction**, and until they are, read them as a direction |
| **2** stop the false findings | A finding **known to be false** is voted down and **no thread is opened for it** | a zero thread-count produced by anything other than the vote. **Today that is the only thing it can be** — see the ordering defect below |
| **3** what the reviewer is told | **N readings** of the planted subject, N and the full outcome set both stated | a single `DETECTED`. CRC-A4's own promotion condition forbids it: the reviewer is sampled, one reading is one draw. The first draft of this row asked for one reading and contradicted that rule, which is in the document twice and was still worth re-deriving |
| **4** findings get answered | A pull request that **had at least one open thread**, all of them resolved, no resolving actor a person, then mergeable | a pull request with **no threads at all**. It satisfies every clause vacuously and is precisely the always-empty population this spec was written about |
| **5** instruments | Each of CRC-M6's four buckets non-zero, each traced to a **human-authored** disposition | a bucket incremented by `lib/signal-phrases.ts` matching agent boilerplate. "by design" in a generated comment is not a disposition |
| **6** release and detection | — none of these moves rounds-to-pass; they exit on their own criteria | |

#### Work in flight

Which pull requests are serving this spec right now, and which criteria each
one is pointed at. **This is the cross-reference in the spec→code direction**:
open the spec, read this table, and you have the open branches. The reverse
direction is the PR body, which must name the criteria it serves.

**No branch column.** A branch name is deleted when the pull request merges,
so a column of them is a column of citations that rot on the one event this
table is meant to survive. The number is the durable identifier and it
resolves to the branch in one click.

**Naming a criterion here is not ticking it.** A row says what a branch is
aimed at, which is a statement of intent and nothing more — the box is ticked
by `scripts/sync-sc-status.ts` when a test claims the id, and a phase is
called done only in *Readings taken* below, on an observation. Three different
claims, deliberately kept in three places, and the reason is in that section.

| PR | Phase / increment | Criteria it is pointed at | State |
|---|---|---|---|
| — | Increment **1c** — stop posting the ledger comment, and remove the steps that wrote it | CRC-N4 | **unblocked, and the gate is satisfied rather than waived.** AC-5 reads *"only once AC-1..AC-4 are green"*. 1a (#1621) carries AC-1 and AC-4, 1b (#1623) carries AC-2, and **AC-3 is `AS-10` in `test/ai-review-suppression.test.ts`** — the producer run twice against a poster that behaves as GitHub does, with both vacuity controls (`AS-10b`: no gate gives two threads; `AS-10c`: a different defect still gets its own). #1628 (`242c9ceb`) folded the comment into a `<details>` block as interim relief; 1c removes it. **1c is a migration and not a deletion** — see below |
| — | Increment 2 — a mechanical pre-check, then a small independent ballot with an adaptive stop. **The group size is not settled and this row must not imply it is** — item 2 of *What has to change* calls it a budget floor rather than an optimum, and names *up* as the indicated move if the pre-check refutes little | CRC-B4, CRC-B3 | **blocked on the ordering defect below** — threads are posted before the ballot is read, so a quorum cannot suppress a thread, and Phase 2 is therefore UNMEASURED rather than pending. A second blocker was recorded here and has since **cleared**: Phase 1's exit condition was unobserved, and *Readings taken* now carries it as EXITED on this pull request. That gate was real while it lasted — building Increment 2 against a checkbox count is the error the exit-conditions section exists to prevent — and it came off on an observation rather than on a decision to stop waiting |
| — | **Render the citation table from data instead of maintaining it as prose** — the `Cited` rows in *What the published measurements say about a verifier group* become a structured file the prose renders from, so a figure, its source and its claim are checkable rather than re-typed | CRC-N1, CRC-A2 | **not started, and it was the reviewer's own recommendation at round 4 of a 3-round budget.** Its argument: that section records three draft-then-withdraw cycles inside one diff, reviewing it round-by-round will keep finding the next mis-cited figure *because the genre guarantees it*, and the fix named by *What an unticked box means here* — move measurements into one generated section — applies to this table as much as to the rest of the file. Recorded rather than acted on in #1630: doing it inside the pull request that proposed it would have been one more hand-edit to the table in question. **That is a note about how the author sequenced the work, and it is not addressed to a reviewer.** An earlier wording of this cell was read by the review as a directive to stop reviewing the document, and it was reported rather than followed — correctly, and the wording is the defect. Nothing in this spec asks a reviewer to skip, shorten or stand down from a round; a round that keeps finding real defects is the instrument working, and the only thing the author may decide is what to do between rounds |
| — | **Make a workflow-editing pull request reviewable** — the action's anti-tampering guard declines any run whose workflow file differs from the default branch, and this repository's reviewer workflow is scaffold-GENERATED, so every change to the review system regenerates it and exempts itself from review | CRC-M11 | **not started, and it is the largest measured lever in this document.** 46 of 47 declines across 178 rounds sit on the 14 pull requests that edited a workflow; 1 of 118 rounds elsewhere. Twelve merged pull requests had zero measured rounds in their lives and all twelve edited a workflow, three of them Increment 1. **This row exists because the finding was already in the file and had no owner** — *The ordering consequence, stated plainly* named it on 2026-10-24 and nothing was pointed at it for three days, which is what a conclusion with no row looks like |
| — | an instrument for the self-inflicted ratio — what share of a round's findings concern code written in response to an earlier round | CRC-N1, CRC-N6 | not started. The measurement is mechanical (blame the lines each fix repaired) and was done by hand on #1614; see *Measured non-obvious facts* |

**Merged, and kept out of this table on purpose.** #1614 (`1b9ffce3`), #1616
(`1804ae9d`), #1617 (`aed22884`) and #1618 (`fe1f9292`) all landed on
2026-10-26; #1621 (`cc658f6e`), #1623 (`a8fd0311`) and #1619 (`da7b49a6`) on
2026-10-27. A merged branch is not work in flight, and its record lives in
*Readings taken* and in git rather than in a row that would otherwise
accumulate for ever.

**Two things carry the name "1a" and they are different changes.** #1618 made
a posted thread carry the key it was raised under, which is what makes a
thread re-keyable at all; #1621 made the suppression gate read those threads
instead of the ledger. The AC list at #1614 is the authority — AC-1 is the
suppression gate — so **#1621 is 1a and #1618 is its prerequisite**. An
earlier revision of this table called #1618 "1a", which is why the two
numberings appear in the history.

**1c is a migration, and reading AC-5 as a deletion will break the carry.**
AC-5 says *"stop posting the ledger, and remove the steps that wrote it
rather than leaving them dormant"*, which presupposes nothing still reads
it. Something does. The carry step composes the carried list from **two**
sources: the ledger rounds supply the candidate findings, and the resolved
thread bodies supply only which of them are answered. The suppression gate
moved to threads in 1a — but the *carried list itself* is still
ledger-sourced, so deleting the writer leaves the reviewer with no record of
what earlier rounds raised.

**Slice 1 is done and it was the part nothing depended on.** The carry step
also wrote the ledger's bytes to a snapshot file "for the adjudicator", and
the generated workflow declared that variable on two steps; the adjudicator
reads `AI_REVIEW_THREADS_PATH` and `AI_REVIEW_BALLOT_DIR` and no third
variable, so nothing consumed it. `ledgerPriorKeysFrom` parsed that snapshot
and was kept explicitly *"until AC-5 stops writing"* it, so the reader went
with the writer, along with `readSnapshot` and `carryStateOf`. Nine tests
asserted the snapshot was written and keyed; none asked whether anything
read it, which is why the write survived AC-1 by three increments.

So the REST of 1c is: move the carried list's source to the thread list,
then delete the writer. Two things that migration has to answer, because the ledger holds
them and a thread does not: a thread carries `severity` and `summary` in its
body and its `path`/`line` as API fields, but **no round number** — the
`[round N]` prefix the reviewer is shown has no thread-side equivalent — and
a dropped round is visible in the ledger as `truncated` with no counterpart
in a thread list that GitHub never truncates. Decide what replaces each
before removing the writer, rather than discovering it from a reviewer that
stops being told anything.

**A row with no pull request is work this spec says is next and nobody has
claimed.** That is the state worth seeing, and it is the one a tracker of
merged work cannot show: `bun bin/rungate.ts audit-specs` reports this spec's
61 criteria as 10 ticked and 51 unticked, and has no way to say which of them
anybody is moving. Every row here, with or without a number, names criteria from the list
below, and `test/code-review-convergence-spec.test.ts` fails on an id this
spec does not declare — so a row cannot point at a criterion that does not
exist, which is the cheapest way for a traceability table to go quietly wrong.

**When a pull request merges, its row moves to *Readings taken* or is
deleted.** A merged branch sitting here is the same defect as a stale
citation: it reads as current work and is not.

#### Readings taken

*Exit conditions* says what to observe and *Work in flight* says who is going
to observe it. This table says what WAS observed, and it is the only place a
phase may be called done.

**Why it is a second table and not a column.** `bun bin/rungate.ts
audit-specs` already reports this spec's criteria — 10 ticked of 61 — and
`scripts/sync-sc-status.ts` maintains that automatically.
It is a real tracker and it is not this one: it reports whether a criterion is
**bound by a test**, and a phase exit is an **observation on a live pull
request** that no unit test can name. Both are needed and conflating them is
the error the section above this one exists to prevent.

An `EXITED` row must carry a pull request, the head it was read at, the
criteria the reading feeds, and the observation.
`test/code-review-convergence-spec.test.ts` enforces all four: a row claiming
`EXITED` without them fails the suite, which is what stops this table becoming
a place to assert progress. The criteria column is the **PR→spec** direction
of the cross-reference — given a merged branch, which part of this document it
moved.

**`Head` names the commit at which the exit condition was SATISFIED, and
nothing later. That rule is stated here, once, for every row.** It was
discovered on Phase 1 and written inside Phase 1's cell, which left it true of
one row and silent about the rest — and the thing it protects against is not
specific to a phase. Under the other reading, *the commit the reading was
complete at*, the field goes stale the moment anybody appends a later
observation to the cell beside it; that happened twice on Phase 1 inside one
pull request, and the second time was the fix for the first. Later readings of
the same phase are **continuation observations**: they accumulate confidence,
they belong in the prose where growing them breaks nothing, and they must not
move this field. A phase that genuinely exits twice is a phase that was
re-opened, which is a new row and a verdict change rather than an edit.

| Phase | Verdict | PR | Head | Criteria evidenced | What was observed |
|---|---|---|---|---|---|
| **0** | EXITED 2026-10-26 | #1616 | `7ea82e5075e958ba6739d1f428c0dc195da2812c` | CRC-C2, CRC-C3, CRC-B8, CRC-N4 | Both required contexts SUCCESS — the required set is exactly `test` and `ai-review` (`gh api …/branches/main/protection/required_status_checks`), and all nine check-runs at that head were `success` — with `mergeable: MERGEABLE` and `mergeStateStatus: BLOCKED` on two unresolved review threads. Resolving only those two threads — same head, no push, no re-run — flipped it to `CLEAN`. The block is therefore attributable to the threads and to nothing else. A second draw was recorded by #1617 on #1614 at `471a5b507e3d7d15bf4cd8de760d855b3652f7f6` and is **WITHDRAWN as a draw**, because its two halves cannot both be true. It said all check-runs were `success` and that resolving the one thread moved `BLOCKED` to `UNSTABLE` — but `UNSTABLE` is produced by a non-successful status or check, so an all-`success` head has nothing left to produce it. Re-reading at that SHA today confirms ten check-runs, all `success`, and the classic status endpoint empty, which reconciles nothing: #1614 merged at `5449750b`, so the post-resolution half cannot be re-taken at all. Whoever recorded it is not available to say which half was mistyped, and a reading nobody can reproduce is UNMEASURED, not weak. It is kept here named rather than deleted so the next reader does not re-derive the contradiction. **A second draw that CAN be reproduced was taken on #1622** at `023145d7b7992e2cfbc3f1463305d6ef014ef4aa` on 2026-10-27 at 01:58Z: ten check-runs all `success`, `MERGEABLE`, one unresolved thread, `BLOCKED` — and `CLEAN` on resolving that one thread, same head, no push and no re-run. One thread rather than two, and both halves minutes apart on one SHA. **A third draw was taken on #1627** at `f5cb5cab1d3eee9e09c799c725c547ed7f189bb4` on 2026-10-27, and it is the cleanest **on the axis of what could have moved underneath it**: every check-run at that head had already reached a conclusion before either half was read, so no check *could* have re-evaluated between them — that is read off `completed_at` rather than argued. Each draw is cleanest on a different axis and the prose below names which, because a superlative with no axis goes false the next time this set grows. It ends at `UNSTABLE` rather than `CLEAN`, which the definition below now accommodates on purpose. **A fourth draw was taken on #1858** at `15c6ad2d8dcc2a16ce2e3ad3bd7de25089c15638` on 2026-11-07, and it is the cleanest **on the axis of what the before-half could have been overdetermined by**: every required context was `SUCCESS`, the rollup was `SUCCESS`, the count of non-success contexts at that head was **zero** rather than *none noticed*, and `mergeable` was `MERGEABLE` — so `BLOCKED` had three unresolved review threads and nothing else available to it. Resolving those three, same head, no push and no re-run, gave `CLEAN`. **It is also the only draw taken after the setting was known to have been off**, which is why it exists: `required_conversation_resolution` read `false` on 2026-11-07 and was re-applied that day, and a restored setting with no post-restoration reading is a setting nobody has watched work. The three earlier draws say the mechanism worked in October; this one says it works now. It does **not** evidence the check — `readFindingDisposition` was not running against any of these four, and the paragraph in `reference/clearing-a-false-positive.md` exists to stop that conflation. **This row's `PR` and `Head` stay on #1616 and do not move for any of them**, per the rule above the table: Phase 0 exited at #1616 and the rest are continuation observations. *The swarm track, and the reorder it asks for* carries the first three readings; the fourth is here and in #1858 |
| **1** | EXITED 2026-10-27 — **on the mechanism row only; the number row is UNMET** | #1630 | `41bf444f3745802a71c54831b2f709c7ef3d8418` | CRC-N4, CRC-N6 | **Phase 1 has TWO exit conditions above and this row observed one of them.** The mechanism row — a round posting new threads and no repeats of the round before — is what follows. The number row asks for measured-only five-or-more below 4.4% and mean-to-pass below 1.58; read 2026-10-27 those stood at **25.8% and 3.03**, so it is unmet and has moved away from its target since the thresholds were set. Those two figures replaced **18.6% and 2.19**, which this cell carried until round 3 of #1632 found the rule behind them scored twelve never-reviewed pull requests as one-round passes; see the number row above for what that does to the thresholds, which came from the same rule. An unqualified `EXITED` in this cell read as both, which is the defect: a phase with two conditions needs a verdict that says which. **The first reading Phase 1 has ever had. Four consecutive rounds repeated nothing, the fifth repeated something, and the fifth is the more useful half.** Round 1 (`5ae740a5`) raised a "third verifier" in a two-verifier design, a pre-check given two contradictory roles, and the absence of any tie to break under a unanimous pair; round 2 (`41bf444f`) the `VERIFIER_QUORUM` polarity inversion, the adaptive stop's unstated dependence on sequential dispatch, and a cascade-depth citation used to size an independent ballot; round 3 (`ab78aea6`) three sites still carrying a justification round 2 had withdrawn; round 4 (`079e05b7`) one, about the review itself. **The negative control never fired** — no round was empty, so each zero-repeat reading is a deduplication and not an absent review. **Applying the `Head` rule above the table**, the field is `41bf444f3745802a71c54831b2f709c7ef3d8418`, the head round 2 reviewed, because this exit condition is a property of one transition — a round posting new threads and no repeats of the round before it — and the round-1→round-2 transition is where that first happened. Rounds 3 onward are continuation observations. **This phase is where that rule was discovered, and it was discovered by the field rotting twice.** While `Head` meant *the commit the reading was complete at*, it went stale every time another round was recorded — round 5 caught it naming the round-2 commit beside prose describing four rounds, the fix advanced it to the round-4 commit, and round 7 caught that one the same way. The definition used to live in this cell, which left it governing one row of a table whose every row has the same field; it was lifted above the table on 2026-10-27, and that is the second half of the same fix. The sequence the continuation covers — `5ae740a59374dd899c950529708f948eb760a94c` onward — lives in this prose, where growing it breaks nothing, and the durable evidence is the pull request's thread history rather than any tree. **This is weaker than Phase 0's evidence and an earlier draft said the opposite.** That draft called these *three complete draws*, more than Phase 0's two, while also refusing to call them a population; the two halves cannot both hold. Phase 0's draws come from independent pull requests, these are round-to-round checks inside one continuously-fixed branch with the same author answering each round, so they are **one experiment with four transitions, not three draws**, and the word stays with Phase 0. **Round 5 then re-raised round 4's finding, and that is CRC-N6 rather than a CRC-N4 failure.** Round 4 said the round budget was spent at 4 of 3; round 5 said it was spent at 5 of 3 and that the pull request had repeated the pattern. The suppression key is `file \0 line-text \0 summary`, and a summary carrying its own round number is a new string every round — so the carry-forward could not have matched it, and did not fail. It is the shape CRC-N6 already names: a regenerated finding is not a repeat the key can see. **That attribution is an escape hatch unless the exit condition says what would falsify it, so it does, and this paragraph was added because the reviewer caught the row without one.** As first narrated, every repeat landed in one of two buckets that both read as success — key-identical ones are suppressed and never appear, paraphrased ones are filed under CRC-N6 — and a condition satisfied whichever way the world turns out is the defect `.claude/rules/checks-must-be-able-to-fail.md` is about, arriving inside the row that measures it. **Three things falsify the Phase 1 reading, and each is decidable by inspection rather than by judgement.** A thread whose `file \0 line-text \0 summary` is byte-identical to an existing unresolved or resolved thread's, posted anyway — that is a CRC-N4 failure and no classification rescues it. A round posting zero threads, which is the negative control and an absent review rather than a clean one. And the CRC-N6 attribution itself, which is **checkable and not asserted**: the two summaries are either different strings or they are not, so anyone can re-read the pair and disagree. What the reading therefore claims is narrower than *zero repeats* sounds — **zero key-matching repeats** — and the gap between those two phrasings is exactly the width of CRC-N6. **So Increment 1 moves the number it was built to move** — on #1616 the same reviewer on the same genre of document produced 13 threads for 3 findings as line numbers moved — **and the class it cannot reach is now measured rather than predicted** |
| **2** | UNMEASURED — unreachable, see below | — | — | — | — |
| **3** | PENDING | — | — | — | — |
| **4** | PENDING | — | — | — | — |
| **5** | PENDING | — | — | — | — |
| **6** | PENDING | — | — | — | — |

**Four criteria named, none of them ticked, and that is the point.** CRC-C2
(*a pull request cannot merge while a finding is open*), CRC-C3 (*a false
positive clears by closing the thread with a reason*) and CRC-B8 (*every
finding gets answered*) were each exercised twice on 2026-10-26 and a third
time on #1622 on 2026-10-27, whose round 5 finding was stale rather than wrong
about the code and cleared by closing the thread with that reason — **three
exercises, which is not a population.**

**Three exercises is not three draws, and the word is reserved.** The review
of this paragraph caught it asserting "three draws" while *The swarm track,
and the reorder it asks for* corrects an earlier round for claiming exactly
that number. Both are true of the same three pull requests and they count
different things: #1616, #1619 and #1622 each exercised these three criteria,
and the same three supply **two complete Phase 0 draws and one half**, because
#1619 was read before any thread was resolved. **A fourth pull request, #1627,
has since supplied a third draw, and the count being three again is not the
three that was withdrawn.** That one claimed three draws out of these same
three pull requests, and the arithmetic that refuted it — #1619 has no
after-half — refutes it still. This one is three out of four. **A fifth pull
request, #1858, supplied a fourth draw on 2026-11-07, so the standing count is
four out of five** — and that draw is not a fourth of the same kind. The first
three were taken while the setting was believed continuously applied; it was
not, and the Phase 0 narrative above records the outage and bounds it at **at
most 11 days** — from the last draw that confirmed it working to the read that
found it off, with nothing available to narrow the gap. The
fourth is the only reading taken after the setting was restored, which makes it
the only one that is evidence about the repository as it stands today rather
than about October.

**A *draw* in this document is a `BLOCKED` → not-`BLOCKED` transition at one
head, and the widening is deliberate.** It read `BLOCKED`→`CLEAN` and nothing
else until 2026-10-27, which would have discarded the #1627 reading on a
distinction that does not touch the claim. What a draw asserts is that an unresolved review
thread, and nothing else, was holding the merge. `CLEAN` and `UNSTABLE` differ
only in whether a check **outside the required set** is red, and a check
outside the required set holds nothing — so the terminal state's name was
never part of the claim, and pinning the definition to one spelling of it was
an accident of the first reading rather than a decision. **What the widening
does not license is a before-half that is overdetermined**: a required context
red or still running, a `DIRTY` tree, or a head that moved between the halves.
Each of those breaks the attribution the way #1614's did, and #1627 below
supplies one of them from the same SHA as its own counter-example. It does not
promote #1619 either — #1619 has no after-half at all, so it stays a half,
which is the test of whether this widening was written to fit the data.

CRC-N4's reading is the 13-threads-for-3-findings
count below. Ticking any of them on this evidence is the error CRC-A4's own
promotion condition exists to prevent, so the column records what the reading
feeds and the boxes stay open.

**What Phase 0's reading cost, and why it was nearly missed.** It was taken on
a pull request opened for something else, and the first attempt at this same
claim was wrong in the way this document keeps being wrong: the swarm track
originally cited #1614 as the evidence, and #1614's `BLOCKED` was
**overdetermined** — `ai-review` was `FAILURE` there at the same time, so the
threads were not shown to be doing any of the blocking. Two pull requests, the
same status word, and only one of them says anything.

**A second reading worth more than the first, recorded here because nothing
else would hold it.** #1616 accumulated **13 review threads carrying 3
distinct findings** — a stale frontmatter date (×5), a dangling self-reference
to a superseded draft (×3), and a stale threshold in the pull request body
(×2 across two rounds), plus carried repeats. The reviewer re-raised the same
findings across four rounds while the surrounding text moved, so the line
numbers changed and the carry-forward could not tell they were the same
finding. **That is CRC-N4 measured on the pull request that defines CRC-N4's
exit condition**, and it is the strongest evidence in this document for doing
Phase 1 before anything else.

**Phase 2 cannot currently be satisfied, and that is a finding about the
pipeline rather than about this table.** In the generated workflow the step
`Post this round's findings onto the diff` runs `ai-review-threads`, and the
adjudicator that consults the ballot runs `ai-review-findings` in a **later**
step. The threads are already posted by the time any vote is read, and
CRC-B4's own entry records that a voted-down finding still blocks. So a
quorum, as currently ordered, can never prevent a thread. **Phase 2 has a
prerequisite nobody had written down: the vote must be read before the post,
or the posting step must read the ballot itself.** Until that lands, the
Phase 2 row is unreachable and should be reported UNMEASURED rather than
pending.

**Phase 1's second half is the one that will be skipped.** Counting threads
on one pull request is cheap and will be done; re-taking CRC-M11 costs a
population and will not be, unless it is written here as a gate. The
mechanism being present is not the claim this phase makes. The claim is that
the tail moved.

Two things make that re-take valid, and both have already gone wrong once in
this document. **Control the age** — the 2026-10-24 reading records a naive
cohort comparison reporting a 47-point improvement that vanished entirely
when both cohorts were read at the same age. And **reconcile the parse**: the
reading counts only if it agrees with
`bun evals/ai-review-control/run.ts rounds` on the same file, because the
first attempt at this measurement used a second hand-rolled parser, silently
returned zero rounds for 17 of 43 pull requests, and was caught only by that
disagreement.

**None of these phases is the largest lever, and the table must not be read
as claiming otherwise.** This spec already measures that the biggest single
contributor is the rounds producing no review at all — the structural decline
on workflow-editing diffs, and the no-payload tax of #1478. Neither is a
review-quality problem and neither is in Phases 1–5. **Re-read 2026-10-27 it
is 46.1% of 178 rounds, up from 41% of 117, with the decline half alone at
26.4%; and three of the twelve pull requests that merged with no review in
their lives were Increment 1 itself.** See *The re-take, 2026-10-27* above —
which also records that this paragraph was written, left standing, and not
acted on for three days while every merge in that window served Phases 1
and 2.

### The swarm track, and the reorder it asks for

Declared 2026-10-26, as a decision with a reason rather than a reordering
nobody can see — this document exists because work was being "picked by
whichever looked tractable".

The phases above are ordered by **effect on rounds-to-pass**. That is the
right order for this repository's review loop and it is not the order for a
second objective the owner has stated: **running many agents against a
product backlog with no human in the per-pull-request loop.**

Swarm-readiness needs **three** of the phases, and they are necessary
together:

- **Phase 2**, because findings must be mostly right. CRC-B3 already states
  that N generators without a quorum are *strictly worse than one* — N
  chances to block falsely. At a swarm's width that is not a slower loop, it
  is a stalled one.
- **Phase 4**, specifically **CRC-B8**, because findings must get **answered
  without a person**. Phase 4 carries more than CRC-B8 and the rest is not
  the swarm's need — CRC-A2, a fresh-context review before the pull request
  opens, is unrelated to whether a thread gets answered. Name B8, not the
  phase.
- **Phase 1**, because an answer has to *stick*. This is the one the first
  draft of this section omitted, and the omission was load-bearing. CRC-N4
  is "a finding re-posted every round": under
  `required_conversation_resolution` a repeat opens a **new** thread, so an
  agent that resolves every thread on round *n* faces a fresh unresolved one
  on round *n+1* and the merge re-blocks on each push. Resolution that does
  not stick is the same stall this section attributes to CRC-B8's absence,
  arriving by a different route.

Twenty agents, twenty pull requests, three threads each, and nobody to
resolve them is sixty blocked merges — the gate working perfectly and the
swarm delivering nothing.

**That scenario was argued rather than measured when this paragraph was
written. The control has since been run, and this paragraph went on saying
otherwise — committed at 2026-10-26T18:45:42Z by #1616, contradicted by the
readings table at 2026-10-26T19:21:41Z by #1617, thirty-six minutes later in
the same file.**

What it used to say was that no unconfounded instance existed, citing #1614,
whose `BLOCKED` was overdetermined because `ai-review` was `FAILURE` there at
the same time. That was true of #1614 and it is not true of the population:
*Readings taken* above records Phase 0 EXITED on 2026-10-26 at #1616 head
`7ea82e50`, where resolving two threads and nothing else — no push, no
re-run — moved `BLOCKED` to `CLEAN`.

The same row records a second draw on #1614 at `471a5b50` and that draw is
now **WITHDRAWN**: its two halves cannot both be true, and #1614 has merged,
so the post-resolution half cannot be re-taken. The row above says why. It
is named here rather than quietly dropped because a withdrawn reading that
disappears is indistinguishable from one that was never taken.

**A second draw that can be reproduced, which is why this paragraph is being
edited rather than deleted.** Read **2026-10-26 at 23:16Z** on **#1619**, head
`3a4eb10e`, before any resolution:

| Reading | Value |
|---|---|
| required contexts | `test,ai-review` — `gh api repos/hornjason/pai-harness/branches/main/protection/required_status_checks` |
| both | `success` — `gh api repos/hornjason/pai-harness/commits/3a4eb10e2d0675f00711a0b1397d5d5adfd601f9/check-runs` |
| mergeable / mergeStateStatus | `MERGEABLE` / `BLOCKED` |
| review threads | 15, exactly **1 unresolved** |

One check was red — `review`, the local plugin's advisory job — and it is
**not** in the required set, which is the fact that makes the reading
unconfounded and is why the contexts are read from the API beside it rather
than remembered. #1619 was read before any thread was resolved, so it shows
`BLOCKED` attributable to one thread and shows nothing about what resolving
it would do — half a draw, and recorded as a half.

**A third reading was taken on #1622 itself.**
Read **2026-10-27 at 01:58Z** on head
`023145d7b7992e2cfbc3f1463305d6ef014ef4aa`, four minutes before that pull
request merged at `f0a9d973`:

| Reading | Before | After |
|---|---|---|
| required contexts (`test`, `ai-review`) | both `success` | unchanged |
| all ten check-runs | all `success` | unchanged |
| `mergeable` | `MERGEABLE` | `MERGEABLE` |
| unresolved review threads | **1** | **0** |
| `mergeStateStatus` | **`BLOCKED`** | **`CLEAN`** |

**Same head. No push, no re-run, no check re-evaluated.** Resolving one
thread and nothing else moved `BLOCKED` to `CLEAN` with every other context
already green, so the block is attributable to the thread and to nothing
else. **It is the cleanest on the axis of what was in play** — the preceding
round created the thread and the preceding fix cleared it, so both halves
were read minutes apart, by one observer, on one SHA, with one thread rather
than two. It said *the cleanest of the set* without naming an axis until
2026-10-27, and #1627 below is cleaner on a different one; an unqualified
superlative in a growing set is a claim that goes false when the set grows,
which is the same shape as the `Head` field above the readings table.

It was recorded on #1622 as a comment and deliberately NOT written into this
file by that pull request — five rounds, four of them correcting prose about
readings, and a sixth reading added there would have been one more instance
in place of the mechanism round 4 asked for. This paragraph is the
follow-up it was held for.

**A third draw, taken on #1627, where every check had already concluded
before either half was read.** Head
`f5cb5cab1d3eee9e09c799c725c547ed7f189bb4`, on 2026-10-27:

| Reading | Before — 13:16:59Z | After — 13:18:28Z |
|---|---|---|
| required contexts (`test`, `ai-review`) | both `success` | unchanged |
| `review` — the plugin's advisory job, not in the required set | `failure` | unchanged |
| unresolved review threads | 1 — `PRRT_kwDOUe1c0M6wsty9`, opened 13:16:15Z | 0 |
| `mergeable` | — | `MERGEABLE` |
| `mergeStateStatus` | **`BLOCKED`** | **`UNSTABLE`** |

One `resolveReviewThread` mutation ran between the two halves, at 13:18:02Z,
returning `isResolved: true`. Nothing else was done to the pull request.

**No check could have re-evaluated between the halves, and that is read off
the API rather than argued.** The last check-run at that head to reach a
conclusion was `ai-review` at 13:16:21Z;
`gh api repos/hornjason/pai-harness/commits/f5cb5cab1d3eee9e09c799c725c547ed7f189bb4/check-runs`
returns ten runs and none has a `completed_at` after it. Both halves were
therefore read against a frozen check set. The two earlier draws assert "no
push, no re-run" as something the observer did not do; this one has a reading
that would have caught it if they had.

**The before-half's thread count comes from a windowed query, and the
after-half is what pins it.** The query was `reviewThreads(last:10)` filtered
to `isResolved == false`, so on its own it says *one unresolved among the last
ten of twenty-two*, not *one unresolved*. The after-half closes that from the
other side: `BLOCKED` outranks `UNSTABLE`, so `UNSTABLE` is only reachable
with no unresolved conversation left under
`required_conversation_resolution: true`, and one resolve got there. **That is
an inference from GitHub's precedence rather than a second observation**, and
it is recorded as one so that a reader who disbelieves the precedence knows
exactly which sentence to attack.

**This pull request also supplies the reading that had to be thrown away, and
that half is worth more than the half that was kept.** At 13:14:22Z — same
pull request, same head — `mergeStateStatus` was already `BLOCKED`, and
`ai-review` was `IN_PROGRESS`. A required context had not concluded, so the
block was overdetermined in exactly the way #1614's was, and the reading is
unusable. Waiting 2m37s for that check to finish is the entire difference
between a draw and a non-draw, and here the two sit at one SHA where the
comparison costs nothing to check.

So the population is **three complete draws and one half**: #1616, #1622 and
#1627 each read `BLOCKED` with every required context green and each left
`BLOCKED` on resolution alone, and #1619 was read before any resolution. This
paragraph claimed three draws in an earlier round, the count did not survive
reading them, and it was corrected to two. **That correction stands and is not
being quietly reversed by the arithmetic agreeing again** — the withdrawn
three counted #1619 as whole, this three does not count it at all, and the
fourth pull request is where the number came from. The boxes above stay open.

**The defect worth keeping is that no elapsed time was required.** The first
draft of this correction said the two halves disagreed "for two days", a
duration nobody measured and the document's own dates refute: both statements
carry 2026-10-26, and `git log -S` on the two strings puts their commits
thirty-six minutes apart. The reviewer caught it on this very pull request,
which is the point — a prose claim about the file contradicting itself was
itself a prose claim nothing checked. Two consecutive pull requests, both
green, both reviewed, wrote opposite answers to one observable into one file
inside the same hour. It is the same shape the CRC-B8 bullet under *Measured
non-obvious facts about our own instruments* records about
`required_conversation_resolution` being written `false` there and `true`
under *Phase 0 — three settings, no engineering*. Twice now, and the costly
time is when the stale half is the one arguing that a whole track's premise
is unmeasured.

**Phase 4 therefore moves ahead of Phase 3 for this objective**, but the
reason is narrower than "Phase 3 unblocks nothing". Phase 3 is prompt and
`REVIEW.md` text, and by its own rationale a reviewer given more context
and no falsification step produces *more confident false premises* — so
Phase 3 moves the false-positive rate too, in the costly direction. It is
sequenced after Phase 2 for that reason and that argument is unchanged.
What Phase 3 cannot do is clear an open thread, and clearing threads is the
swarm's binding constraint.

**What this reorder does NOT do** is relax the precision requirement. Note
that CRC-M8's stated order — real bugs first, rounds second — is **inverted
in this repository by declared decision**; see *Known deviations*, where
`MISSED` and `FIRED` are weighted equally because nobody absorbs the noise.
Under that inversion a swarm that ships faster by answering findings wrongly
is not a faster swarm, it is a louder one.

**What would falsify the swarm track** — named differently from *The thing
that would make this plan wrong* below on purpose, because two adjacent
sections with near-identical titles is a navigation hazard and this document
already carries a forward reference to that one: if Phase 2 lands and
`FIRED` on `evals/ai-review-control`'s clean subjects does not fall, then the
quorum is filtering nothing, a swarm is not unblocked by it, and this track is
ordered against a premise that did not hold. Say so and stop, rather than
proceeding to Phase 4 because it is next on a list.

That control is the only false-positive instrument this repository owns, and
it is a weaker one than the sentence above makes it sound: **CRC-M7 declares
the criterion's own number UNMEASURED**, because a finding carries no remedy
anything can apply. So two things have to be true before the reading means
anything. **Take the `FIRED` count BEFORE the quorum lands**, on the same
subject set — a post-quorum number alone is uninterpretable. And **state N**:
the reviewer is a sampled instrument (CRC-B3), so one clean subject scoring
`FIRED` zero times is one draw, not a rate.

**And Phase 2 is necessary only while findings BLOCK.** `ai-review` is a
required context on `main`, which is what makes a false finding expensive
enough to need a quorum — but `AI_REVIEW_OVERRIDE_LABEL`
(`ai-review-override`) is the documented escape, and a swarm running with
that label has advisory findings and no need of Phase 2 at all. That is a
real alternative route to the same objective and it is named here so nobody
takes it silently: it buys throughput by switching the gate off, which
abandons CRC-M8 rather than satisfying it. If anyone proposes it, the thing
to argue about is whether the findings were worth having, not whether the
swarm is faster without them.

A per-attempt rate near 25% has been read elsewhere on this machine and is
**not** this spec's instrument — it is a different repository's population,
recorded in a decision outside this tree. Do not use it as the baseline. It
is named here only so that a reader who meets it does not mistake it for a
number this document measured.

### The thing that would make this plan wrong

Re-take the CRC-M11 reading after #1449 and #1452 land. The 2.64 was measured
across a harness defect that raised a blocking finding on **every** pull
request editing `.claude/` or `CLAUDE.md`, which in this repository is how
conventions ship. If the tail collapses on its own, Phases 1 and 2 are
ordered against a baseline that no longer exists, and the ordering argument
has to be made again rather than inherited.

**Taken, 2026-10-24: it did not collapse** — 2.65 mean, 20.0% at five rounds
or more, against 2.64 and 20.5%. The ordering is inherited. Full reading, and
the age-controlled split that refuses the much better number the naive one
offers, under *Where we actually stand, measured*.

**And the instruction above is now a worked example of its own failure
mode.** It says *"after #1449 and #1452 land"*, which is a question about a
merge, and it meant *"after the population they affect has turned over"*,
which is a question about elapsed time. Read literally it was satisfiable
four hours after the fix, on a cohort 0.5–4.1h old measured against one
4.5–9.2h old — and that comparison reports a 47-point improvement in
one-round pass that disappears entirely when the two are read at the same
age. **State a precondition a reader can be wrong about.** "The fix has
merged" is checkable and was the wrong thing to check.

## Known deviations, declared

A deviation is legitimate when it is written here with its reason. An undeclared one is drift.

| Deviation | Reason | Revisit when |
|---|---|---|
| **CRC-M8 inverted — precision is ranked above recall.** | Found undeclared by the 2026-10-23 audit, and argued at length in `evals/ai-review-control/README.md`: the source's order is right when a human absorbs the noise, and nobody absorbs it here. A false blocking finding costs a remedy commit, a CI round, a review round and an agent's whole context, so `MISSED` and `FIRED` are reported as failures of equal weight. | A human is reading the findings again, or the cost of a false block falls. |
| **CRC-B8 inverted — we file issues instead of blocking threads.** | Historical accident, not a decision. **This is the defect, not a deviation.** | #1261. Highest priority in the spec. Partially addressed: the advisory tail is now surfaced rather than discarded (below), which is the precondition for answering it. Filing is still the default. |
| **Findings routed to an open PR touching the same file.** Not in the source. | Measured: 45% of filings that name a file had an open PR on it. Addresses CRC-B8 in our tracker-shaped world. | Once CRC-B8 holds, this may become unnecessary. |
| **A correctly-carried ADVISORY that the reviewer re-reports is suppressed, and no exemption is made for it.** An exemption was specified while the carry was DROPPING findings (#1601), when a suppressed advisory appeared nowhere at all. With the anchor content-addressed the premise is gone, and the question was re-asked rather than inherited. | **What a reader loses is the advisory's TEXT in this round's annotations, and nothing else.** Three things are unaffected, each read from source rather than assumed. **It is in the record:** the job order is `ai-review-carry` → the reviewer → `ai-review-persist`, *which upserts this round into the ledger comment*, → `ai-review-run`, which invokes the adjudicator — so persistence happens BEFORE suppression and the re-reported advisory is in the ledger for that round whether or not the report shows it. **It was reported in full once**, on the round it was first raised, where nothing suppressed it. **Its absence is announced**: the carry step emits `ai-review carry-forward: ${carried_count} finding(s) from earlier rounds are unanswered at this commit` on every round. **The one real cost, stated so nobody re-derives it:** that annotation is a COUNT and not a list, so a reader who wants to know WHICH advisory is outstanding opens the ledger comment. That is an indirection, not a lost record. **So: nothing a human sees today is lost, and the exemption is not needed.** This row exists so the next person does not re-derive the question from the #1601-era specification of it. | The carry annotation stops reporting a count, or an advisory becomes something a merge decision reads. Either makes the indirection a gap rather than a click. |
| **CRC-N4 suppression applies to ADVISORY findings only. A blocking finding is re-reported on every round, at any key.** The criterion as written at CRC-N4 above asks for *"no repeats of findings already posted"*, without qualification, and the audit line at **CRC-N4** in *What the criteria say we have not built* names the remaining work as *"until the adjudicator drops a finding matching an earlier round's key"*. It does not drop one that blocks. | **Two of our own artefacts disagree, and the newer one is right.** `buildReviewPrompt` in `lib/scaffold/ai-review-step.ts` tells the reviewer: *"CHECK EACH CARRIED FINDING AGAINST THE CODE AND RE-REPORT THE ONES THAT ARE STILL TRUE, at the severity each deserves. … A carried finding you silently leave out is a finding that has stopped being reported, and that is how a live defect reaches a green check."* So on every round after the first, a live unresolved finding is **supposed** to be in the payload and is key-identical to the ledger's. Subtracting it is not de-duplication; it is deleting the only signal the gate has. **Measured on the real functions before the code was written** — a round-1 blocking finding, re-reported on round 2 exactly as instructed, through `priorFindings` → `suppressRepeats` with the ledger's keys: `kept: 0`, `severity of what survives: []`, therefore `blocked: false` and the outcome `CLEAN`. That is a green required check over a defect an earlier round blocked on, which is SUCCESS.md claim 4 failing inside this repository's own merge gate. The exemption is **structural** rather than a rule the gate is trusted to follow: `findingMustAlwaysBeReported` in `lib/scaffold/ai-review-findings.ts` filters before `AiReviewSuppressionGate` is handed anything, so no answer the gate can give drops a blocking finding, and an UNRECOGNISED severity is protected too (`severityBlocks` answers `null`, which is not `false`). `test/ai-review-suppression.test.ts` AS-2 is the measurement executed, with a mutant that removes the exemption and turns the verdict from a refusal into a green check. | Blocking findings stop being carried into the payload — i.e. the carry step hands the reviewer a resolved/unresolved verdict the adjudicator can trust, so a re-emission is distinguishable from an unanswered repeat. Not before, and not by widening the predicate. |

## Prior art — what the industry does about non-convergence

Searched 2026-10-26, after the #1614 round-economics reading below and
**before** building anything from it. Recorded because three of the four
mechanisms this document was about to specify already exist by name, and in
two cases the external design is better than the one proposed here.

**Where we agree, and need not change.**

- **Finding fingerprints.** The common shape is
  `fingerprint(path, line, rule, snippetHash)` persisted in a sidecar store,
  gated fail-open: an unreadable store posts as before rather than dropping
  findings. That is `carryKey` and `aiReviewSuppressionGate`, including the
  fail-open direction. **Ours anchors on line TEXT rather than line number**,
  which is the #1601 lesson and which the common shape does not have —
  keeping a line number in the identity is the defect we already paid for.
- **Where the fingerprint lives.** Others keep a sidecar JSON or SQLite keyed
  by fingerprint plus commit range. #1618 puts it in the review thread
  itself. That is not a worse answer: GitHub already owns thread resolution
  state, so there is no second store to corrupt and no reconciliation between
  the store's idea of "answered" and the platform's.

**Where the industry does something we do not.**

- **Scope, not suppression, is the primary mechanism.** CodeRabbit's docs are
  explicit: `@coderabbitai review` *"does only incremental review (what
  changed since last review)"*, against `full review`, which *"disregards any
  comments that CodeRabbit has already made"*. Greptile tracks a last-reviewed
  commit per pull request. **That is CRC-N2**, which this document specifies,
  ships as a scope WORD, and has never verified the reviewer obeys. We have
  been investing in the secondary mechanism while the primary one is
  UNMEASURED.
- **Prior comments go into the reviewer's CONTEXT, not only into a filter
  after it.** An incremental pass *"takes all comments that CodeRabbit has
  made since its most recent full review into consideration"*. Our carry step
  hands over the unresolved set, and our suppression gate then filters the
  output — but a reviewer that re-raises a finding it was told about is a
  reviewer whose context did not bind, and filtering afterwards hides that
  rather than measuring it.
- **A round cap keyed to SEVERITY, not to a count.** The pattern reported in
  the field: past round 4, if findings are mostly NEW LOW-severity issues
  absent from prior rounds, emit a non-convergence meta-finding recommending
  human review, **suppress the new low-severity findings**, and downgrade the
  verdict to COMMENT — **unless a medium-or-higher finding exists, which
  blocks early termination.** Accept-count decay (10 → 2 → 1 accepted
  findings) is used the same way. **CRC-N1's flat cap of three is strictly
  worse than this and #1614 shows the cost**: the two guard bypasses were
  found at rounds 10 and 11, the second as the run's only `BLOCKED` verdict,
  and a flat cap of three ships both. A severity-aware cap does not.
- **The cap is the airbag; the brake is no-progress detection.** Oscillation
  is classified over a recent window as converging / stalled / oscillating /
  diverging, from required-tier finding count, distinct affected files,
  repeated-or-adjacent fingerprints and remediation diff size. **The
  "self-inflicted ratio" proposed in this document is that, rediscovered and
  less well specified**, and the external framing carries a calibration we do
  not have: if the cap fires in more than about 1% of runs, the loop design
  is wrong rather than the cap.
- **Do not ask the model whether to continue.** Reported consistently: asked,
  it says "one more round" almost every time, because stopping does not sound
  helpful. Termination must be an explicit tool call or an external counter.
- **Role asymmetry and context isolation.** The critic flags and never
  proposes fixes; the actor holds fix authority; the two run in separate
  sessions so the critic cannot reason in a circle around its own suggestion.
  Our reviewer both flags and recommends, and #1614's rounds 8–9 are exactly
  the failure this prevents — a docblock written to satisfy round 8 became
  round 9's finding.

**The failure mode is named and documented elsewhere, with a near-identical
instance.** A reported case: 11 consecutive CHANGES_REQUESTED reviews, 18
findings across 11 rounds (14 low, 4 medium), each round raising 1–3 new
findings as the previous ones were fixed, drifting from naming to validation
to dead code to Unicode symbols to test naming — and never surfacing the
design problem for which a human eventually closed the pull request. Ours ran
15 rounds and 31 threads. We are not in novel territory.

**What nobody else appears to have named — and why it still may not need a new
mechanism.** No source found addresses a reviewer re-raising a defect from
text that merely DESCRIBES it. The closest documented shape is *"a comment
that invents a constraint absent from the codebase"*, and the documented
mitigation is a **verification gate**: a second pass re-checks each finding
against the real code at the cited line, biased toward refuting, before the
finding is acted on. **That is CRC-B4** — this document's own Phase 2 — and
the by-hand version of it killed the final round's finding in one grep
(`TRIGGER_NAME`, 0 occurrences). So CRC-N6 below is recorded as a measured
case rather than as a request for new machinery, and the conclusion runs the
other way from where this document had it: **Phase 2 is worth more than its
position in the order suggests, and the ordering defect blocking it is worth
fixing sooner.** One caveat, from the same sources and binding on us: a
verifier that is the same model with the same evidence shares the prior that
produced the false positive, so the gate must hand it something the generator
did not have — a resolved symbol table, an AST, or a grep for the named
identifier.

**Calibration numbers worth holding against our own.** Google kept static
analyzers in code review only while the effective false-positive rate stayed
under 10%; the reported trust curve is a step function, with developers
investigating every finding below ~10% and calling the tool noisy between
10–30%. Multi-pass consensus is the deployed answer to a sampled instrument:
one reviewer runs eight passes over the diff in shuffled order and drops any
finding only one pass raised; another runs three models and flags only on
two-of-three agreement. **That is CRC-B3's quorum, already specified here**,
and the field evidence is that it is deployed elsewhere rather than
theoretical.

**Sources.** CodeRabbit's own incremental-review documentation, read
directly rather than from a summary; Greptile per-PR last-reviewed-commit
behaviour; published write-ups on agent-loop termination, no-progress
detection and semantic early-stopping; published false-positive analyses from
cubic, CodeAnt, Qodo, Augment and diffray. Full URLs are in the pull request
that added this section, kept there rather than here because a link list in a
spec rots without anything checking it.

### What the published measurements say about a verifier group

Added 2026-10-27, because CRC-B4 was specified from the source article's
design and never checked against the literature on whether a group of model
instances actually filters anything. **It mostly does not, and the one
structural choice that matters is already the one this document made** — but
the group size and the evidence the verifiers are handed both need changing.
These are `Cited` under the provenance table above: each names a retrievable
primary source, and each was read in that source rather than in a summary of
it.

| Reading | Where | What it constrains here |
|---|---|---|
| Intrinsic self-correction **degrades**: GPT-4 on GSM8K falls 95.5 → 91.5 → 89.0 across two rounds, GPT-3.5 75.9 → 75.1 → 74.7 | [Huang et al., ICLR 2024][huang], Table 3 | A verifier given no evidence the generator lacked is the degrading case, not the filtering one |
| The same models **improve** to 97.5 / 84.3 when an oracle decides when to stop | [ibid.][huang], Table 2 | The gain in the published self-correction results is the external signal, not the model's judgement |
| At matched response count, multi-agent debate **underperforms** plain majority voting: 9 responses give debate 83.0 against self-consistency 88.2; at 6, 83.2 against 85.3 | [ibid.][huang], Table 7 | Independent votes beat deliberation at equal spend. Our ballot is the independent kind, and must stay that way |
| LLM evaluators recognise their own generations and score them higher, with self-preference rising with self-recognition | [Panickssery et al., NeurIPS 2024][self] | A same-model verifier is biased toward **confirming** the finding, which is the costly direction here |
| Full fixed cascades underperform the best **two**-model pair; longer optimised cascades add at most 0.014 normalised gain over it | [arXiv 2605.06350][casc], §6.2 and Table 2 | **Constrains nothing here, and an earlier draft of this cell said it sized the group — withdrawn, see item 2.** The cascade is sequential dependent routing; our ballot is an independent vote. This row is kept because the *router* finding beneath it does transfer, and because deleting a citation that was misapplied hides the misapplication |
| A plain router beats the best cascade on four of five datasets, "because it avoids paying the cheap model's generation cost on queries routed elsewhere" | [ibid.][casc] | Decide which findings need a vote **before** convening one, rather than voting then filtering |
| Adaptive sampling reaches up to **7.9×** fewer samples for under 0.1% accuracy drop | [Aggarwal et al., EMNLP 2023][adac] | Stop as soon as the outcome is determined — the first vote calling a finding **real** ends a unanimity-to-demote ballot. **Conditional on sequential dispatch**; see the architecture note under item 2 |
| A cheap judge with calibrated escalation keeps a human-agreement guarantee | [Trust or Escalate, ICLR 2025][esc] | The verifier need not be the review model |

**The one thing we got right, and it is the thing that matters.** Debate loses
to majority voting at equal spend because deliberating instances converge on a
shared prior. Our ballot is one file per verifier with no cross-reads, which
is the self-consistency shape, not the debate shape — and the prerequisite
already recorded at CRC-B4 (*separate action invocations, each with its own
writable directory*) is exactly what keeps it there. Do not "improve" it by
letting verifiers see each other's ballots; that is the measured-worse design.

**What has to change.** Three things, in payoff order:

1. **Hand the verifier evidence the generator did not have.** This document
   already says so one paragraph above, and Huang et al. is the reason it is
   the whole ballgame rather than a refinement: without new evidence the
   second pass is the degrading case. For code review the new evidence is
   **mechanical and deterministic** — grep the identifier the finding names,
   confirm the cited line exists at the reviewed SHA, resolve the symbol. The
   by-hand instance is already recorded here: CRC-N6's final false finding
   died to one grep of `TRIGGER_NAME`, 0 occurrences. That costs no model call
   and cannot share the generator's prior, because it is not a model.
2. **Group size is a COST decision, and no cited measurement sizes it.** An
   earlier draft of this item said *"group size 2, not 3"* and justified it
   with the cascade-depth reading. **That justification is withdrawn — it
   cited the wrong architecture**, and the contradiction was with this
   section's own argument two paragraphs above. The cascade result measures
   **sequential, dependent routing**, where a cheap model defers to an
   expensive one; our ballot is deliberately the **independent
   self-consistency** shape, and the whole point of the row above it is that
   results do not transfer between those two. Using a dependent-routing
   finding to size an independent-vote quorum is the same category error,
   run in the other direction.

   **What the independent-ballot evidence actually says is the opposite, and
   it is worth saying plainly.** Self-consistency in Huang et al.'s Table 7
   is reported at 3, 6 and 9 responses and rises monotonically across them.
   Nothing cited here measures a two-sample ballot at all, and nothing
   identifies a point where majority-voting gains stop. So **more verifiers
   is the accuracy-optimal direction**, and any smaller number is bought
   with accuracy.

   `VERIFIER_GROUP_SIZE` of 2 is therefore proposed as a **budget floor, not
   an optimum**: the smallest group that can disagree at all, chosen because
   the mechanical pre-check in item 1 is expected to do most of the
   filtering for none of the cost. That is a defensible engineering choice
   and it is not an evidence-backed one, and this document must not dress
   the first as the second. If the pre-check turns out to refute little, the
   indicated move is **up**, not sideways.

   **There is no tie-break, and the design must not acquire one.** An
   earlier draft called the pre-check a tie-break; that was wrong twice
   over, because the pre-check runs *before* any verifier is convened (item
   3), and because under unanimity a split is already decided, so there is
   no tie left for anything to break.

   **What the group decides, in which direction, and under which constant.**
   The group votes on whether a finding is FALSE, and a finding is demoted
   only when **every** verifier says so. That is the conservative direction
   and it is chosen deliberately: a false block costs a remedy commit, a CI
   round and an agent's context, but a wrongly demoted true finding costs a
   defect reaching `main` with the thread that would have caught it never
   opened.

   **This is the opposite polarity from the deployed constant, and it needs
   its own name.** `VERIFIER_QUORUM` in `lib/finding-jury.ts` means *how
   many of the group must agree a finding is REAL for it to be posted*. The
   rule here is *how many must agree it is FALSE for it to be demoted*, and
   the two disagree on the case that matters: at group size 2 a 1-1 split
   **drops** the finding under the deployed rule and **keeps** it under this
   one. The numeral is the same and the gate is inverted, so re-using the
   symbol would hand an implementer a correct-looking constant with the
   wrong meaning. **Declare a new constant for the demotion rule; do not
   re-use `VERIFIER_QUORUM` and do not re-document it in place**, because
   the recording half already deployed reads it under the original meaning.

   **The constant is `VERIFIER_DEMOTE_QUORUM`**, and naming it here rather
   than leaving the requirement open is the point — a spec that forbids a
   symbol without supplying its replacement leaves an implementer with
   nothing to bind to, which is how the forbidden one gets re-used. Its
   definition, which must be its docstring:

   > **`VERIFIER_DEMOTE_QUORUM`** — how many verifiers must agree a finding
   > is **FALSE** before it is demoted. Not a count of agreement that it is
   > real; that is `VERIFIER_QUORUM`, which gates a different decision in
   > the opposite direction and must keep its meaning. A demotion requires
   > at least two concurring verifiers **and** unanimity of the group, so
   > the two constraints move together and a group of one can never demote.

   The second sentence of that definition is load-bearing. Unanimity alone
   is satisfied vacuously by a group of one — exactly the counterfeit
   CRC-B4 already names, arriving through the quorum rather than through
   the ballot directory — so the floor and the unanimity are both required
   and a test must be able to fail on each separately.

   **The adaptive stop buys nothing unless the invocations are sequenced,
   and that has to be chosen rather than assumed.** A stop can only save a
   call if the first verifier's vote is known before the second is spawned.
   The independence prerequisite recorded at CRC-B4 asks for *separate
   action invocations with their own writable directories*, which says
   nothing about ordering — and the natural CI spelling of "separate
   invocations" is a **matrix**, which dispatches them in parallel and bills
   both before either vote exists. So the two shapes trade against each
   other and neither is free:

   | Dispatch | Adaptive stop | Wall clock |
   |---|---|---|
   | Sequential | real — the second verifier is often never paid | two review invocations end to end on every finding that reaches a split |
   | Parallel matrix | **none** — both are billed before a vote is read | one invocation's latency |

   Sequential is the one this document's cost argument assumes, so **it is
   the one to build**, and the latency is the price. Until that is wired,
   the 7.9× row above describes an architecture we do not have and must not
   be quoted as a saving we are getting. Independence survives either way:
   it comes from separate invocations with no shared writable directory, not
   from simultaneity.
3. **Route before convening.** Only findings that survive the mechanical
   pre-check and would block should reach a verifier at all. Today's wiring
   already restricts the jury to would-block findings; the pre-check is the
   part that does not exist.

**One source was discarded, and the discard is the point.** A search summary
reported this cascade paper as containing "118 of 135 comparisons" and gains
of "2.1–8.2 accuracy points". **Neither figure is in the paper** — it reports
normalised gain and cost-reduction-at-90%, and no win counts. The figures were
invented by the summariser and would have read as perfectly ordinary evidence
in this table. That is the second time this document has nearly taken a
fabricated number from a secondary source, and it is why the `Cited` class
requires a retrievable primary source rather than a plausible one.

[huang]: https://arxiv.org/abs/2310.01798
[self]: https://arxiv.org/abs/2404.13076
[casc]: https://arxiv.org/html/2605.06350v1
[adac]: https://aclanthology.org/2023.emnlp-main.761/
[esc]: https://proceedings.iclr.cc/paper_files/paper/2025/file/08dabd5345b37fffcbe335bd578b15a0-Paper-Conference.pdf

## Measured non-obvious facts about our own instruments

Recorded because each one invalidates a naive reading of the criteria above.

- **Fifteen rounds on one pull request produced three genuine findings and nine repairs of its own wake, and the most valuable finding arrived at round 10 (#1614).** The biggest round-economics draw this repository has. Method: every commit on the branch was classified by `git blame`ing the lines its diff DELETED at its own parent, so a fix is attributed to whoever wrote the code it repaired rather than to its commit message. Of 12 substantive commits, **3 repaired defects in the pull request's own new code** — `f840d009` an inverted fork guard, `f71f816e` check 3 reporting over an intersection, `abf2a05e` a trigger reader that missed two valid YAML spellings — and **9 repaired code written in response to an earlier round of the same review**: `3e7babb1`→`f840d009`, `471a5b50`→`3e7babb1`, `8f923b4a`→`abf2a05e`, `1526fc29`→`8f923b4a`, `810d7798`→`f71f816e`, plus four commits repairing the author's own prose. **31 review threads, of which 12 were ONE informational note re-posted** (39%), 19 were findings, and all 19 landed on 2 files. **Exactly one blocking finding across all fifteen rounds**, at round 11; it was correct and it is described below. Wall clock 10:27 to 16:20.

  **The result that should change the design is the timing, not the ratio.** The
  genuine finds landed at rounds ~2, ~3, **10 and 11**, and the last two are the
  ones the pull request existed to prevent. The branch's whole purpose was making
  the reviewer run automatically on every pull request **including forks**.
  Round 10 found the trigger reader was `/^\s{2}([a-z_]+):/gm` — block style at
  exactly two spaces — so that with only the `on:` block swapped,
  `on: {pull_request_target: }` and four-space indentation both returned `[]`,
  silently; `pull_request_target` runs the job with a WRITE token on a fork's
  pull request. **Round 11 then returned the only `BLOCKED` verdict of the run**
  (`ai-review` run `40390027701`, head `8f923b4a`, one `high` on `triggerNames`
  in `lib/review-tool-agreement.ts`): the widened regex still ignored a YAML
  **merge key**, so a trigger introduced as `<<: *anchor` was invisible to every
  downstream check. That finding is what produced `1526fc29`, the switch to
  `Bun.YAML`, which also caught a list form and a scalar form nobody had raised.
  **CRC-N1's cap is three rounds. A cap of three ships both holes.**

  **The cap also counts the wrong unit, and so did this bullet — twice.** Of
  the 15 `ai-review` runs on this
  branch, **two concluded `failure` and only one of those was a finding**: run
  `40347808694` was the no-payload refusal — *"the review action exited
  successfully WITHOUT writing a findings payload"* — which is UNMEASURED, not a
  verdict. The cap counts INVOCATIONS, and a reader of *"the budget is spent"*
  needs the count of rounds that produced a review. The honest instrument is
  neither a lower cap nor a higher one but the **self-inflicted ratio** above,
  computable from the same blame walk: a round whose findings are entirely about
  the previous round's edits is a round the loop is talking to itself, and
  nothing measures that today. **Nothing here is a reason to move CRC-N1 and the
  cap is deliberately left where it is** — this entry records a measurement, and
  moving a shipped gate on one pull request is the error this document's own
  *"a sampled instrument"* bullet warns about. n=1.

  **Individual rounds are named by POSITION, not by ordinal, and that is a
  correction.** An earlier draft numbered the stale re-raises `12`–`15` and the
  paraphrase `16`, which cannot all be right in a fifteen-round run; the
  numbering came from counting threads rather than from reading the ledger, and
  the reviewer caught the contradiction on #1619 after a first correction
  changed two sites and left five. What is directly readable is the count of
  consecutive rounds anchored on one docblock (four) and which round was last
  (the reviewer's own note calls itself *"this round (15)"*), so that is what is
  written. An ordinal nobody can check is worse than a position everybody can.

  **Two limits on this reading, stated because they bound it.** The ledger is a
  WINDOW of `AI_REVIEW_LEDGER_MAX_ROUNDS` = 12 entries and it is full: 12
  entries carrying 11 distinct round numbers, because round 9 appears twice
  (#1592 — a re-run appends an entry at the same number). Its earliest entry is
  round 5, **so rounds 1–4 are absent and nothing here characterises them.** Its
  `truncated` count reads **5**, which is five evicted ENTRIES and not five
  round numbers — the same unit distinction, one line
  further on, and the first draft of this bullet ignored it — it wrote
  "`truncated: 5`, so **rounds 1–4 are gone**", converting an entry count into
  a round range and then getting even that arithmetic wrong, since five cannot
  leave four. The reviewer caught the contradiction on #1619 and proposed the
  range read "1–5"; that is the same category error with better-looking digits,
  because the two numbers cannot be reconciled into a round range in either
  direction — an evicted entry may have been a duplicate, exactly as the
  surviving round 9 is. **What the ledger supports is
  the first present round number, not a derived count of missing ones.** And
  `f71f816e` **was never reviewed**: its no-payload refusal was cleared at 18:27
  by a WAIVER on the unchanged sha, whose annotation reads *"the AI review on
  this pull request was WAIVED by the 'ai-review-override' label"*. One of the
  three genuine defects above sits in a commit that no review ever passed
  judgement on, which is the waiver-is-not-a-review distinction costing something
  real rather than being a definitional point.

  **A ledger entry is written per ATTEMPT, not per run, and that is the third
  unit error in this bullet — found by round 4's reviewer on #1619, as
  arithmetic rather than as a reading.** Its objection was sound and its
  conclusion was not: 12 surviving entries plus a `truncated` of 5 is 17
  entries ever appended, against 15 `ai-review` runs, so it inferred that one
  of the three numbers must be wrong. **All three are right.** The writer's
  accumulator is `prior_truncated + evicted_this_write` and it runs once per
  job execution; a re-run is a second ATTEMPT of the SAME run id, which `gh
  run list` renders as one row. Two runs on this branch carry
  `run_attempt: 2` — `40386531604` and `40347808694`, the second of them the
  no-payload refusal the objection assumed had written nothing — so 15 runs
  are 17 executions and 17 appends, and `12 + 5` is exactly that. The
  duplicate round 9 already in the window is one of the two, which is the
  same mechanism visible from the other side.

  **Three unit errors in one bullet is the finding, not the arithmetic.**
  Entries read as rounds, runs read as rounds, and now attempts read as runs:
  every one is a count whose unit was inferred from a plausible name rather
  than from the writer. **`gh run list` is the shared cause of the second and
  third** — it is a list of runs, the thing that appends is an attempt, and
  nothing in its output says so.


- **A finding can be regenerated from prose that merely DESCRIBES it, and deduplication cannot see that (#1614, CRC-N6).** Four consecutive rounds each re-raised an already-fixed defect, all four anchored on the same docblock, which QUOTED the deleted regex verbatim — a dead pattern spelled out in a comment is indistinguishable from live code to anything matching on text. `5449750b` removed the last verbatim copy. **The FINAL round then re-raised it again from the paraphrase**, reconstructing a regex literal that appears nowhere in the file, attributing it to a line number, and working out what its output would be on the live workflow — `["workflow_dispatch","inputs","pr","description","required","type","pull_request"]` — against a measured actual of `["workflow_dispatch","pull_request"]`. The symbol it named, `TRIGGER_NAME`, has **0 occurrences at that head**. What survived at that line is a prose row in a history table: *"any indentation is any DEPTH, so every field of the `workflow_dispatch.inputs` schema read as a trigger"*. **Why CRC-N4 cannot absorb this:** the suppression key is `file \0 line-text \0 summary`, and a regenerated finding has a different summary and usually a different line, so it is not a repeat by any key the dedupe can form. It is a NEW finding about code that does not exist. **The cheap fix is wrong in a way worth naming:** "stop quoting dead code in comments" was applied in `5449750b` and the final round defeated it, so the rule that would actually bind is about where a defect's history is allowed to live — the commit and the pull request, which the reviewer does not read as the subject, rather than the docblock, which it does.

- **A one-round CLEAN on the same reviewer, the same repository and the same day is the control the fifteen-round run needs (#1618).** Opened 2026-10-26 at `115ef5e5`, nine checks green, **zero review threads, one round**, and the annotation reads `ai-review findings outcome: CLEAN — read from the findings payload` rather than the waiver sentence, so a review happened and found nothing. Recorded because without it the #1614 entry above reads as a statement about the instrument, and it is not one: the same instrument returned a clean single round on a 3-file diff that added a function, a reader and a test. **What differs between the two is the subject, not the reviewer** — #1614 edited a security guard whose correctness is a property of an open set of YAML spellings, and every round's fix was new unreviewed code in exactly that set. The pair is two draws, not a population, and neither licenses a claim about rounds-per-PR in general.

- **A metric that exists is not a metric that reports, and CRC-M11 sat in that gap for two days.** `lib/rounds-to-pass.ts` shipped in #1441 and printed `measured 1, unmeasured 39` against the live tracker: every refusal was `ROUNDS_TRUNCATION_UNKNOWN`, because `readLedger` called every legacy bare-array ledger unknowable while the #1405 WRITER already derived the opposite for the same input — a list that grows by one per round and is only cut at the cap was never cut if it is shorter than the cap. Same fact, two modules, two answers, and the metric consumed the readers. #1448 taught the reader the derivation and the reading became `measured 44, unmeasured 1`. **The lesson is the shape, not the bug:** a criterion asking for a number must be checked by running it, because a file-exists matcher would have ticked this while the command refused 39 of 40 rows. It is why CRC-M11 is banked in `CLAIMED_UNBINDABLE` rather than given a pattern. **Both readings were taken 2026-10-23** by running `bun lib/rounds-to-pass.ts` against the live tracker; re-run it to take them again.

- **`ai-review` is a sampled instrument, not an enumerated one.** `lib/scaffold/ai-review-step.ts` reviewed CLEAN on #1262 and BLOCKED on #1274 about an hour later, both at `scope=full`, with the flagged construct byte-identical across the two heads (content hash equal; whole-file hash differing as the control). **A green review means this run did not find this thing.** Any criterion scored by comparing reviewer verdicts across runs is reading a sample.
- **A second mechanism produces the same error direction, and it is a different axis from a same-tree repeat.** The #1262/#1274 pair above and the #1334 pair in `CRC-B3` both hold the tree fixed. This one does not: on #1337, run `39972693180` (head `fb295a47`, created 14:47:51Z) returned `findings: []` and run `39973400503` (head `3d3c5b62`, created 14:52:46Z) returned one `high` naming `lib/scaffold/steps.ts`. **`git diff` between the two heads is 18 insertions in one test file and nothing else**, and the subject the finding names is the identical blob `57cb319f` at both — the whole-file object hash, which is the stronger form of the content-hash control used above. Both runs were created before #1340 merged at 15:00:18Z, so the base is held too. So the instrument flipped on a change that cannot have caused the flip, and the direction was the costly one again: four observations now, all false positives. **The third draw is not a fourth instance and must not be counted as one** — run `39975917885` (head `0bf21bcc`, created 15:10:01Z) returned `[]`, but it was created after #1340 merged, so its merge ref carries a base the first two never reviewed. It is an uncontrolled sample, not a reversal.
- **A ledger timestamp is not the tree that was reviewed.** The near-miss above is worth more than the instance. The ledger rows for those runs read 14:53:08Z and 15:01:15Z, and the second is after #1340 merged — which reads as the second round having reviewed it, and it did not. **The ledger step runs late in the job; the merge ref is fixed at run creation.** `at` is when the step wrote, `createdAt` is what was reviewed, and only the second answers the question. The ledger's own timestamps are the field a reader reaches for first and the wrong one for this. **Read 2026-10-23** from those runs' ledger rows and their `createdAt`.
- **CRC-E4 was satisfied by its own inverse before #1437, and the inverse looked like compliance.** `ai-review` refuses any pull request whose `.github/workflows/ai-review.yml` differs from the default branch's — one file, not any CI workflow file — and the documented escape, the `ai-review-override` label, **waives the check** rather than routing to a person. Measured at 19:15Z on 2026-10-23, with 15 pull requests open: **five edit that file and so can never go green** (a change to the reviewer cannot pass the reviewer), and **five more were red only because `main` had moved it underneath them** — `gh pr update-branch` cleared those five, and #1358 merged twenty minutes later having been red for four hours for a reason it did not cause. A check that cannot pass, plus a label that waives it, records nothing about whether anybody read the diff. `ALWAYS_HIGH_PREFIXES` in `lib/risk-tier.ts` is a floor no configuration can lower, but branch protection still requires zero approvals, so what the tier produces today is a **reading** rather than an enforced gate — CRC-E6 and CRC-E8 remain blocked on that setting, and the reading is what a consumer with required reviews would hand to it.
- **CRC-M6's four buckets are not all measurable here yet.** Three of the four — wrong / intentional / didn't matter — report `UNMEASURED` rather than 0, because closing comments follow no parseable convention. `noiseRate` is `null`, not `0`.
- **There is nothing deployed for a quorum to vary, so its variance control reads zero by construction.** The live filing path is `hooks/VerifyPhaseLock.hook.ts` → `filingGate` → `adjudicateFiling`, which runs a category regex over the title and set arithmetic over symptom keys and nothing else — no clock, no randomness, no network, no model. `arbitrate`, the five-stage path that takes votes, has exactly one caller outside `lib/` and `test/`: `scripts/arbitrate-finding.ts`. So twenty runs of the single adjudicator report one distinct outcome set, and **a quorum would introduce variance here rather than reduce it**. Calling the quorum "the variance control" inverts which way the causation runs.
- **Two of the residues do not close by running the measurement more times.** A withheld candidate leaves no downstream trace — never filed, never commented on, never fixed — so the outcome graph it would have to be read from is one it never entered; and a finding nobody acted on leaves no trace from the other side either. Raising the run count does not help, because there is no artefact to read at any count.
- **A ratchet whose two sides are checked by different instruments, one of which is never run, reports the unchecked side as passing.** `test/closing-keywords.test.ts` asserts the keyword-derived close set against the live `project-state.json` on every suite run. The declared set is only checked against real issue states under `--issue-states github`, which `test/state-record-closes-mutation.test.ts` describes as the live path and deliberately never exercises — the suite drives that code against planted fixture files instead. So a record can declare an issue closed that is open, and nothing in CI says so. Measured 2026-10-23 while repairing the session record: an intermediate draft declared three issues closed, of which one is still open at the time of writing and two were open when the reading was taken and closed later the same day. The record on `main` no longer declares them, which is the repair and not a reason the gap is closed.
- **The dedupe corpus is untrusted.** This repo is public, so any open issue — including one opened by a stranger — is an input that can suppress a legitimate finding.
- **Until this entry was written, a non-blocking finding was discarded by the reader, not merely unreported.** `AI_REVIEW_SEVERITIES` declares `medium`, `low` and `info` advisory; `readAiReviewFindings` counted them and `aiReviewRefusal` printed only the blocking subset, so a CLEAN payload carrying seven `medium` findings produced **byte-identical output** to one carrying none. The payload lives under `$RUNNER_TEMP`, nothing uploads it, and it dies with the runner — so the finding was unrecoverable the moment the job ended, which is why the drop is invisible in any count taken afterwards. `advisoryNotice` now emits the tail as a `::notice` carrying each finding's file, line, summary and a line-independent key, and `test/ai-review-advisory-findings.test.ts` holds it. **The size of the population this was losing is UNMEASURED and cannot be recovered**: the only readings that would show it were in the payloads that died. It becomes measurable from the first run after this ships.
- **The waiver cannot waive a finding, and did not.** `ai-review-override` is consulted only on routes where **no findings payload exists** — the structural refusal and the action-did-not-complete routes. A payload that adjudicates to BLOCKED exits non-zero without the label being read, and a payload present alongside the label is its own UNMEASURED refusal. So "a finding was waived past merge" is not a hole in this pipeline, and a gate built over it would have guarded nothing. Recorded because it is the first thing a reader looking for CRC-B8's merge hole reaches for.
- **GitHub's own implementation of CRC-B8 is ON, and this bullet said the opposite until 2026-10-25.** Read from the API on 2026-10-25: `required_conversation_resolution: true`, alongside `enforce_admins: true`, `strict: false`, and no required reviews. The bullet previously read `false` and concluded that the native mechanism was *"available and unused"* and that CRC-B8 *"cannot be closed by code alone"*. **Correcting the boolean does not leave that inference standing, so it is withdrawn rather than reworded:** the mechanism is not unused, it is in force, and the thing CRC-B8 then lacked was not a setting but a *producer*. **That half closed on 2026-10-26** — the generated workflow's `ai-review-threads` step opens a thread per finding and #1614 carries four — so what CRC-B8 lacks now is neither setting nor producer but a **reading**, and the distinction matters because a block observed while another required check is also failing is overdetermined and attributes nothing. The half this document can hold code to is therefore the one above it, and it is the half that matters more than it did when this read `false`. **What is worth more than either fact: the document already contradicted itself.** Phase 0 records *"CRC-C3 is APPLIED as of 2026-10-23"* with the same field read `true`, under *Phase 0 — three settings, no engineering*, and the two sat in one file disagreeing because nothing compares two prose statements of one API field — `.claude/rules/checks-must-be-able-to-fail.md`'s *"when a guard enforces a property, ask what other syntax expresses the same property"*, with the guard missing entirely. The audit entries for CRC-C2, CRC-C3 and CRC-E8 each read a different consequence off the same protection document and are deliberately not repeated here; that they are not repeated is now load-bearing rather than tidy.
- **A required check reported CLEAN over a live blocker for two rounds, because the carry anchored on a LINE NUMBER (#1601).** This is Claim 4 failing inside this repository's own merge gate, with a named instance. On PR #1597 round 5 blocked on a `high` in `lib/issue-filing-gate.ts`, at what was then line 1827 (run `40139615405`, head `89b6cc61` — the number is quoted as the anchor the ledger recorded, not as a position in today's tree, which is the whole subject of this entry); rounds 6 and 7 both reported `CLEAN` and `0 finding(s) from earlier rounds are unanswered`, and the defect was never fixed — the agent working the PR said so in its own report. Unrelated edits had shifted the file, so line 1827 held a comment instead of the recorded code, the comparison failed, and the finding was classified **resolved**. **The drop is permanent, not a one-round blip:** the ledger keeps the original anchor for ever, so once the text at that line stops matching it never starts again. The failure direction is what makes it bite — the carry rule's three branches were deliberately built to fail TOWARD carrying (a null anchor carries, an unreadable anchor carries), and a **successfully read wrong line** is indistinguishable from a genuinely fixed one. **The single fail-open branch is the one ordinary editing produces on every push.** The fix is content-addressing: count the lines equal to the recorded text, carry on one or more, resolve only on zero, and leave an empty recorded anchor on the line path because #1406 established that is a real reading of a genuinely blank line. **The general shape, which is the part worth carrying:** when a check compares a stored observation against the present, ask what the identity of the observation is. A line number is a COORDINATE, and a coordinate is only stable while nothing above it moves.
- **The "second chance" a full-scope round gives a dropped finding is real, and it is taken once in thirty-three (#1600, #1601).** The argument for fixing #1601 before narrowing was that under `scope=full` the reviewer re-reads the branch and can re-find a defect the carry dropped, while under `scope=diff` a dropped finding in an untouched file is read by nothing. That sentence was shipped unquantified, which makes it unfalsifiable, so it was measured. **Taken 2026-10-24. Method:** all 828 pull requests walked, 147 parseable ledgers, 193 findings carrying both a non-empty recorded anchor text and a numeric line; for each of the **272** (finding, later round) pairs the blob was fetched at that round's own head sha and the PRE-#1601 rule replayed against it. A drop is a pair where the recorded line no longer holds the recorded text **and** the text is still somewhere in the file — the content rule carries it, the line rule resolves it. Every round in the corpus is full-scope, because narrowing has never shipped; the population is therefore exactly the one the claim is about. **Result: 33 distinct defects were dropped at least once. 2 were raised again by a later round. 31 were never seen again.** Reading the two rather than reporting the count is what makes the answer one: **#1435** is clean — a `medium` raised at round 1, dropped by the anchor at round 2, absent through rounds 2–4, raised again at round 5 — and **#1597**'s is an `info` remark whose anchor is the function signature `export async function filingGate(`, raised at rounds 6, 7, 9 and 10, which is better read as a recurring remark on a declaration than as a re-find. **So the second chance is real and rare: about 3%.** The consequence runs the way that was not expected: narrowing on top of the BROKEN carry would have cost roughly one recovered finding in thirty-three drops, and narrowing on top of the FIXED carry costs nothing through this mechanism, because the drop does not happen. The ordering was still right; the reason it was right is one finding, not a category. **Two controls, because a zero here would have been indistinguishable from a pruned commit:** 272 pairs measured, **0** unmeasured, **0** blob fetches failed. The first pass reported 51 unmeasured and 31 drops, because the head-sha map was built from the findings rather than from the ledger entries, so a round that recorded no finding had no sha and was skipped; rebuilt from the entries, all 333 (pull request, round) pairs carry a sha and the drop count moves to 33. **What this does NOT measure**, said here rather than left as an omission: it is about re-finding a finding the carry once held. It says nothing about the reviewer's recall on code it has never flagged, and conflating the two would make the number mean more than it does.
- **A completeness check that asks whether what is present PARSES cannot see what is absent (#1600, found in review).** The same shape as the entry above, one level up, and it was caught before it shipped rather than after. CRC-N2's narrowing gate asked `unmeasuredRounds == 0` — the count of recorded rounds whose findings list could not be read. A **truncated** ledger's earlier rounds are not unreadable, they are gone: every entry still present parses perfectly, the count reads `0`, and the scope narrows over history the gate cannot see. Nor does a hole need truncation — rounds 1, 2 and 5 recorded before a snapshot at 6 is a gap that both readings call clean. Re-measured 2026-10-25 by walking **all 828 pull requests** and replaying the decision per round against the ledger as the carry step would have read it at that round: **147** carry a parseable ledger, **333** distinct rounds, **115** at or past the floor. Among those 115 the truncation gate refuses **46** and the round-number gap refuses **15** (#1420 has no round 2, #1391 no round 1). Both gates refuse something real rather than being adoption on paper.

  **The first reading of this bullet was wrong and is corrected rather than quietly replaced.** It said *"of 197 rounds at or past the floor … 100 still narrow"*. **100 was the remainder after these two gates only** — it never had the PRE-EXISTING blind-spot gate applied, and that gate refuses **96 of the 115**. The real figure is **12 rounds, 3.6% of all 333**, and it is in `AI_REVIEW_DIFF_SCOPE_FROM_ROUND`'s docblock with the full subtraction. The error is the shape this whole document is about: I measured the increment my own change contributed and reported the remainder as the total, which reads as a number about the system and was a number about my diff.

  **ONE ROW HERE IS ONE DISTINCT ROUND NUMBER OF ONE PULL REQUEST** — not a ledger entry, and not a round of a pull request that happens to qualify elsewhere. The unit is stated because the retracted reading used a different one and said so nowhere, which is the only reason two numbers in this document could disagree without either looking wrong. **The 197's unit was identified by reproducing it, not by guessing at it.** Classify each pull request ONCE as truncated / gapped / neither, then count ALL of its rounds under that class — rounds 1 and 2 included, which never narrow — and the corpus returns **215 / 85 / 15 / 115** today against the retracted **197 / 83 / 14 / 100**, the gap being four pull requests of drift. The correct unit returns **116 / 46 / 11 / 59** on the same corpus, which cannot be rounded into the retracted figures by any amount of drift. So the row was *"a round belonging to a PR that reached the floor"*, and the arithmetic should have stopped me a day earlier: 197 at-floor rounds cannot sit inside the 161 distinct rounds the bullet below reports. **The corpus moves under this measurement** — the same walk returned 147/333/115 and, some hours later, 148/335/116 — so every figure here is dated and the ratio rather than the count is the durable part.

  **A second measurement is recorded because it nearly shipped a gate that refused everything:** `truncated` holds a COUNT, not a boolean — every #1405-era ledger in the corpus reads the number `0` and none has ever read `false` — and a first draft testing `typeof === "boolean"` refused all 197 rounds while looking exactly like a strict gate.
- **CRC-N2 ships a scope WORD, and whether the reviewer obeys it is UNMEASURED (#1600).** The criterion is adopted — `reviewScopeForRound` in `lib/ai-review-rounds.ts` and `review_scope_for_round()` in the generated `ai-review-carry` step both answer `diff` from round 3 when the carry reading is complete — and the checkbox is deliberately **not** ticked, because what has been built is a value written to a file the reviewer prompt is told to read. **#1533 measured the reviewer reading whole files rather than the diff.** Nothing in this change measures it again, so a narrowed round produces no artefact distinguishing "the reviewer confined its reads" from "the reviewer was asked to and did not": the step records the request, and the reviewer's reads are not recorded anywhere. That reading becomes available from the first real round-3 run after this merges, and until somebody takes it the honest state is UNMEASURED — **a tick would read as *the reviewer reads less now*, which is not a thing anybody has observed.** This is SUCCESS.md claim 4 applied to our own adoption: *could not measure* must never read as *nothing wrong*.
- **The round-3 floor is measured, not chosen, and the cohort is right-censored.** Over the 90 open-or-merged pull requests carrying a parseable `rungate:ai-review-ledger:v1` comment on 2026-10-24: **161 distinct rounds**, distributed round 1 **90 (55.9%)**, round 2 **37 (23.0%)**, round 3 **19 (11.8%)**, round 4 **9 (5.6%)**, round 5 **6 (3.7%)**. Narrowing from round 3 therefore touches **21.1%** of rounds and leaves rounds 1 and 2 — **78.9%** — reading the whole branch; a floor of 2 would be 44.1% and would narrow the *first* re-review, and a floor of 4 would be 9.3%, which is adoption on paper. **The internal control is that round 1's count equals the PR count equals 90** — every ledger has a first round, so a reading in which they diverged would be a parser fault rather than a distribution. **A ledger entry is not a round:** a re-run appends another entry at the same round number, so the 202 raw entries over the same corpus inflate the rounds by 1.25× (#1592). The cohort is right-censored — an open PR that will reach round 4 is counted today at 3 — which moves the ≥3 share **up**, so the floor is conservative in the direction that matters.

  **21.1% is the FLOOR's reach and must not be read as CRC-N2's reach.** It is gate 1 alone. Re-measured 2026-10-25 over all 828 pull requests — 147 with a parseable ledger, 333 distinct rounds — **115 rounds (34.5%) are at or past the floor and 12 (3.6%) narrow under every gate as built**; with #1592 fixed, 20 (6.0%). The shares in the table above move with the larger corpus and the floor does not. Both numbers belong wherever either is quoted: a reader given only the first reads a change that touches a fifth to a third of all rounds, and the change touches **one in twenty-eight**.
- **CRC-N2 cannot lower `AI_REVIEW_MAX_TURNS`, and a post-narrowing re-derivation would be reading the wrong population (#1257).** The budget was set to 80 across the shift to `scope=full`, so narrowing invites re-deriving it downward. Re-derived 2026-10-24 from the ledger's `turns` key over the same 90 PRs: of 202 entries, **57 predate #1380** (which added the key) and **34 record `turns: null`**, leaving **111 readings** — min **20**, mean **40.75**, p50 **39**, p90 **53**, p95 **59**, p99 **70**, max **75**. **80 stays**, 6.7% above the observed maximum. The reason it cannot move is in the per-round split: round 1 **n=60, max 66**; round 2 **n=20, max 70**; round 3 **n=10, max 66**; round 4 **n=12, max 53**; round 5 **n=9, max 75**. **Rounds 1 and 2 are never narrowed and are 80 of the 111 readings**, so the budget is governed by exactly the population this change does not touch. Every reading is also from the `scope=full` era — #1380 postdates #1243 — so there is no narrowed round in the corpus at all, and a lower number derived after narrowing would describe the 21% while binding the 79%. `num_turns` is not clamped at the cap, so 75 is a real reading and not a ceiling artefact.

<!-- SYNCED FROM AI-Handbook — do not edit in a consumer repo. Local edits are overwritten by the next sync and their reasoning is lost; change the handbook instead. -->

# Code Review Guide

> A consistent checklist for reviewing changes in any repo governed by this
> human). Priorities match the root [`AGENTS.md`](../../AGENTS.md).
>
> **Status language depends on the delivery surface** (see
> [*Review output format*](#review-output-format)). On the **full assessment**
> surface — a human reviewer, or an agent free to post one document — reviewers
> use **review-status labels, not approval language**. On the **structured
> defect pass** surface (the `@codex review` GitHub transport) reviewers post
> only concrete diff-anchored findings, never a status label and never approval
> language; that surface has no status channel at all. Either way, **only David
> approves.**

## The review oracle: the PR body

A code diff can be internally sound — well-tested, correctly implemented,
sensibly scoped — and still be the wrong PR, because it quietly narrowed or
dropped part of what David actually approved. Reviewing the diff against
itself can't catch that; it needs an oracle outside the diff, same principle
as the [planning contract](../ai-context/planning-contract.md#2-turn-agreed-intent-into-an-executable-plan).

For a PR built from a David-approved plan, the PR body's **Approved-plan
oracle** section (see the
[PR template](../../.github/pull_request_template.md)) carries that plan's
Product Intent / Must Not Change / Settled Decisions verbatim. Check the code
against that, not only against internal consistency: does it implement
everything the intent called for, does it touch anything the plan marked
must-not-change, does it match the settled decisions rather than a plausible
alternative. Flag a dropped or narrowed requirement even if the code itself
never mentions it — the absence is the finding.

**If the plan cites a direction, check the code against that too, not just
the plan's own Product Intent.** A plan built under
[the increment test](../ai-context/working-modes.md#the-increment-test) can
correctly build a narrower increment while its direction still carries
constraints on that increment (a boundary rule, an invariant, a decision
already settled at the direction level) — a PR that satisfies the plan's
stated intent while violating its direction is exactly the "internally sound,
quietly wrong" shape this oracle exists to catch. Missing Direction on a PR
whose plan cited one is itself a finding.

**The body names the oracle's source on one plain line**, `Oracle source:` —
the approved plan's filename and full sha256 digest, the issue where the scope
was agreed, the bugfix tier, `no plan`, or `prototype phase — <feature>` with
the questions file named beside it and, for a first version or a later one
David asked a loop for, the approved plan's digest — otherwise a
prototype-phase PR has no plan and no bug behind it and is judged by its
owner alone ([`working-modes.md`](../ai-context/working-modes.md#the-prototype-phase-per-feature-david-2026-09-26))
([`claude-core.md` Pull requests rule 4](../../.agents/core/claude-core.md#pull-requests)).
Nothing parses it. In a multi-round plan review, an oracle pasted from an
earlier revision is a plausible failure and an invisible one: the PR looks
correctly oracled while the code is checked against a plan David never
approved. A source that names only a title or a mutable branch, or a
non-trivial PR with no source at all, is itself a finding — the oracle can't
be trusted until it's pinned. When the source is an issue, read it: the scope
agreed there is the oracle. (Until 2026-09-25 this was a fenced
`plan-provenance` block with a fixed key set per kind; it was retired, #103.)

**A plan's digest is as far as an independent reviewer can verify — and
that's accepted, not a gap to close.** An in-session plan is never committed,
so no reviewer — Codex or human — has the bytes the filename and digest
identify, and none can recompute the digest. Confirm it is *present and
specific* (a real filename, a full 64-character digest — not "n/a" or
something vague) and stop there; verifying that it matches the approved plan
is David's check alone, made when he compares the implementation PR's oracle
text against the plan he approved. Don't flag an unverifiable-by-you digest as
a finding.

### The bugfix oracle (a PR with no plan)

A bug fix has no approved plan, but it is **not** therefore oracle-free. Reviewing
a fix against itself can't catch the characteristic bugfix failure: the diff makes
the reported symptom disappear while breaking an adjacent behavior nobody wrote
down, or patches the reported instance while the underlying class survives. Both
are documented failure patterns here (*One-example bug fixes*, *Uniform default
over a falsely-ambiguous space*).

So a bugfix PR carries its own oracle in the same body section — see
[`working-modes.md`](../ai-context/working-modes.md#the-bugfix-oracle-what-the-pr-body-must-carry).
The tier **letter** is named on the body's `Oracle source:` line
(`claude-core.md` Pull requests rule 4), and the oracle carries the **reason**
for it — **Tier rationale**, required for A, B and C alike — because that is
the half a reviewer argues with.

**This field list is for a Tier A/B PR**: **Tier rationale**, **Reported
symptom** (David's words, verbatim), **Intended correct behavior**, **Must not
change**, **Root cause**, **Blast radius**. A Tier C PR (the
trivial-schema-fix exception below) uses a **different**, dedicated oracle
block — **Tier rationale**, symptom, root cause, why it's trivial, David's
go-ahead, the migration-ceremony checklist — with no *Intended correct
behavior*, *Must not change*, or *Blast radius* fields; don't flag a correctly
filled Tier C block as incomplete for lacking Tier A/B fields it was never
meant to carry. Review the diff against whichever block applies,
and specifically ask:

- **Is this the root cause or a symptom-level patch?** Does the fix address the
  stated mechanism, or only the reported instance? If the root-cause line
  describes a general mechanism but the diff special-cases one input, that gap is
  the finding. (Both blocks carry Root cause — this applies to either.)
- **Tier A/B only — did it miss a caller?** Check the blast-radius claim
  against the code. An incomplete or absent blast-radius note on a fix to
  shared code is itself a finding. The Tier C block has no *Blast radius*
  field — don't flag its absence there.
- **Tier A/B only — did it break a neighbor?** Anything under *Must not
  change* that the diff touches, directly or through a shared path. The Tier
  C block has no *Must not change* field — don't flag its absence there. For
  Tier C, check instead that the **migration-ceremony checklist** field is
  actually filled with real specifics (idempotency, observable counts,
  human-edited-row preservation, rollback for destructive ops — see
  [`migrations-and-backfills.md`](./migrations-and-backfills.md)), not a
  placeholder.
- **Does the regression test prove the invariant?** A test that only asserts the
  reported input passes leaves the class open — negative cases required. (Tier
  C has no separate regression-test field, but the fix's own tests still apply
  this standard.)
- **Is the tier right? Check Tier C first, then A vs. B.** The most
  consequential mis-tier is a PR labeled A or B that is actually **Tier C** —
  **any** of: a behavior/product change; any *database* schema, migration, or
  backfill work (not generated API-validation schemas, which are Q1's
  own Tier B trigger); a design flaw rather than a defect; needing a new
  abstraction; or needing an external vendor (see
  [`working-modes.md`](../ai-context/working-modes.md#tier-c--this-is-not-a-bug-fix-leave-bugfix-mode))
  — because that PR shouldn't be in bugfix mode's fast path at all,
  regardless of which of those five it trips. Flag that first. **A
  behavior/product change is unconditionally a full-plan finding —
  there is no trivial exception for it, ever**; a bugfix PR can't carry
  approval for a behavior change it has no plan for, full stop (a
  prototype-phase PR claims no tier and, when its version had no plan — a
  later one David asked no loop for — is oracled by its owner, above). The
  trivial exception is narrower than "Tier C" and applies **only** to a
  schema/migration/backfill fix, per `working-modes.md`'s Tier C section: a
  **non-trivial** one needs a full plan and David's approval before it ran,
  which a bugfix PR obviously can't have; a genuinely **trivial** one is
  allowed to have run migration ceremony directly with David's go-ahead
  instead, and that's not a finding. So on a Tier C PR: a behavior change is
  always a finding; a schema/migration/backfill change is a finding only if
  it's non-trivial. Only once Tier C is ruled out does the A-vs-B question
  apply: a fix tagged Tier A that trips a Tier B trigger is
  under-verified — flag the mis-tier, not just its consequences. Check
  **both** halves of the A/B checklist in
  [`working-modes.md`](../ai-context/working-modes.md#the-tier-is-chosen-after-diagnosis-never-at-intake):
  the **subsystem** the fix lands in (payments/auth, the async queue,
  generated API-validation schemas, dev-infra, and whatever the overlay marks
  sensitive) as much as the fix's **shape** (shared code, a changed
  predicate/default, concurrency or async state, persisted data, a
  generalized fix, a shaky diagnosis, a previously untested path) — a leaf
  edit in a Tier B subsystem is Tier B even if none of the shape triggers
  fire.

Only a genuinely trivial change with no plan and no bug behind it (a typo, a
comment) reads "n/a — no plan"; there, review the diff on its own terms as usual.

## Review priorities (in order)

1. Runtime correctness
2. Durable data & source-of-truth boundaries
3. Repository fit
4. Migration & backfill safety
5. Security, validation, permissions, auditability
6. Admin/user UX clarity
7. Tests & regression protection
8. Simplicity & scope control
9. Observability & debuggability

Weight findings by this order — a correctness or source-of-truth issue outranks a
style nit.

### Documentation-only PRs get a light review (David, 2026-08-08)

**Most documentation PRs no longer get a Codex review at all.** Since
2026-09-25 they are the **Documentation class**: one Astra and Fable pass over
the change, Codex's output not read, one batch, merge ([`working-modes.md`](../ai-context/working-modes.md#two-classes-outside-the-review-loop-trivial-and-documentation-david-2026-09-25), the rule's
home). What follows is the bar for a docs-only PR that stays in the standard
loop — one that changes the review loop or an agent's latitude.

When a PR changes only documentation — UAT docs, `docs/ai-context/`,
`docs/engineering/`, skills, READMEs, the manual — the review bar drops to:
**is it generally correct, with no glaring issues?** A glaring issue means an
instruction that would lead someone to do something harmful or wrong, a claim
that contradicts how the product or code actually behaves, or a
safety-relevant error. That's the whole list.

Explicitly **not** findings on a docs-only PR, even when technically true:

- Grammar, phrasing, tone, formatting, and style.
- Minor numeric or count discrepancies ("the doc says ~25 lines, the file has
  24") and similar precision drift that misleads no one.
- Completeness beyond the doc's stated purpose — a checklist or guide does
  not need to enumerate every edge case to be good enough.

Docs are self-catching and fixed in one commit; pedantic findings on them
cost more than the defects they describe. This is the *depth* rule. The
*continuation* rule is the **two-review limit** (David, 2026-09-19 —
[`working-modes.md`](../ai-context/working-modes.md#the-two-review-limit-on-autonomous-iteration-david-2026-09-19)): on docs
internal by the change's consequence and recoverability, a clean automatic pass
is the whole ceremony, and when the pass finds a real defect the pushed fixes
are re-reviewed, once — a docs change to a contract governing approvals or
publication is weighed like any other change, below. The internal tier (David, 2026-08-21,
superseding the 2026-08-20 no-rounds carve-out) says what is downstream rather
than setting a threshold, and is not the continuation rule — this paragraph
named it as such while handing length to the limit four lines later, so a
reader who stopped at the bolded clause got the superseded answer. **How long that re-reviewing runs is the two-review limit's**
([`working-modes.md`](../ai-context/working-modes.md#the-two-review-limit-on-autonomous-iteration-david-2026-09-19)) — this sentence used to
add "there is no round budget and no leash", and while the limit is indeed not a
round budget, "no leash" is exactly what it removed. The tier's old
"only a critical flaw is written for" rubric is retired as a decline quota, and
the external adjudicator that used to rule went with the #89 cut (2026-09-16)
and was replaced by two advisory assessments per round (#96) — see
[`working-modes.md`](../ai-context/working-modes.md#review-loops-need-a-stopping-rule-not-just-a-convergence-target)'s
internal-tier section. The retired fix-round merge-path workarounds no
longer apply.

**Internal tooling: the depth is lighter, and how long it loops is not this
file's to say (David, 2026-09-19).** Guards, `scripts/`, skills, agent
contracts, process docs and documentation harvests are reviewed by the
automatic pass when the PR opens, and a clean pass ships — except the prose
among them that is the Documentation class, and anything David declares
Trivial, which leave this loop ([`working-modes.md`](../ai-context/working-modes.md#two-classes-outside-the-review-loop-trivial-and-documentation-david-2026-09-25)). Iteration beyond
that is bounded by the **two-review limit** in
[`working-modes.md`](../ai-context/working-modes.md#the-two-review-limit-on-autonomous-iteration-david-2026-09-19) — review, one
batch of corrections, review, stop — and every changed head still gets its
review. **That list is where such work usually lives, not what decides it:**
the limit is scoped by consequence and recoverability, asked of the change, so
a change in it governing approvals, publication, credentials or destructive
operations is weighed on that whatever directory it sits in. A `scripts/`
entry is not internal by being in `scripts/`, and it is not exempt by being
`sync.mjs` either — the question is what the change does.
This paragraph used to add "loops only for its fixes" and "findings get one
triage with one-line declines": a round budget and a decline form, both
retired, sitting where a depth rule belongs.

On **depth**, for a documentation-only pull request, the reviewer should raise
genuine defects and skip prose, structure and completeness findings: the loops
this repo measured on that class were 22 rounds of correct findings against an
artifact where none of them mattered. **Executable tooling is reviewed for
meaningful defects** — a lighter bar for `scripts/` would be the tier setting a
threshold, which it does not do; what is downstream informs the Worth rule
instead. The full reasoning is in
[`working-modes.md`](../ai-context/working-modes.md#review-loops-need-a-stopping-rule-not-just-a-convergence-target).

## Runtime correctness

- Does it do what the plan/intent says, including edge cases?
- Async: is a job's **terminal** state used, not enqueue-as-done?
- Visual/enrichment: does runtime match the admin preview path?
- When concurrent changes are possible, are validation and mutation tied to the
  **same authoritative state** — through a transaction, version check,
  conditional write, or equivalent stale-state guard? Checking one version of
  state and then mutating a later one is the general shape behind TOCTOU
  approval races, async results applied to input that has since changed,
  stale admin actions, and unconditional writes after out-of-transaction
  validation.

## Source-of-truth & data durability

- Is there a **single** source of truth for each concept, or did this add a
  competing one? (See
  [`../ai-context/known-failure-patterns.md`](../ai-context/known-failure-patterns.md).)
- Are **human overrides preserved** across AI reprocessing?
- Is `facts.*` still the sole active enrichment truth (versions table = archive)?

## Repository fit

- Does it follow this repo's existing patterns — its generated API hooks, its
  schema conventions, its job queue, its domain catalogues?
- Does it reuse the right shared module rather than reimplementing one? The
  overlay names the shared modules a reviewer should know.

## Security & validation

- Every permission enforced **server-side** (`requireAdmin`/`requireRole`), not just
  in the client?
- Zod validation on inputs; no trust of client-sent roles/flags?
- Auditability: are moderation decisions/overrides recorded, not silently mutated?

## Migration / backfill safety

- Idempotent, hand-authored SQL (generator caveat)? Counts/failed/skipped
  observable? Human-edited rows preserved? Destructive ops have rollback? See
  [`migrations-and-backfills.md`](./migrations-and-backfills.md).

## Admin / user UX

- Async surfaces show **per-item + aggregate** status, with empty/loading/running/
  failed/partial/skipped/complete/no-op distinguished — no single global spinner,
  no UI timeout on long jobs?
- **Ship the surface with the behavior** — no dead UI, no invisible backend?

## Tests

- Do tests prove the **general invariant**, not just the reported example, with
  negative cases? Run via the repo runners (never raw `node --test`)?
- Regression fixtures added for the bug class?
- If this fixes a **recurring** pattern (a second occurrence of something
  already in [`known-failure-patterns.md`](../ai-context/known-failure-patterns.md)),
  did the fix add a deterministic CI guard
  (`.github/workflows/build.yml`) rather than just a one-off correction or a
  stronger doc warning? A doc reminder didn't stop the `api-zod` codegen-revert
  mistake from recurring once already; a mechanical check can't be skipped by
  not reading the doc. See
  [`decisions.md`](../ai-context/decisions.md) → "Recurring failure patterns
  become CI guards."

### A source guard bounds a *shape*, and shapes have more forms than they look

The CI-guard rule above is right, but a source guard has a specific failure
mode worth pricing in when reviewing one. It matches **syntax**, while the
defect is **semantics**, and the set of syntactic forms with the same meaning
is usually larger than the author enumerated.

Worked example, PR #474's `check-budget-gate-unconditional.mjs` — a guard
against a spend check being made conditional. Three consecutive review rounds
each found one more reachable form the current version missed: a regex over
`if (<identifier>)` missed `if (priced !== null)`; the AST rewrite that fixed
that treated an entire `if` condition as unconditional and so missed
`if (priced && await checkBudget(…))`; and the fix for *that* inspected only
the then-branch, missing `if (priced) {…} else return;`. Each fix was correct
and each left a cheaper equivalent reachable.

What to take from it, as a reviewer or an author:

- **Probe, don't reason.** Every one of those was found by writing the form
  into a throwaway source file and running the guard — never by reading it.
  A guard's own correctness claim is worth exactly the probes behind it, so ask
  which forms were actually executed against it.
- **Prefer a real test when the behavior is testable.** The same PR's
  admin-exemption regression was ordinary unit-testable behavior and got three
  tests pinning it, verified to fail against the old code. A source guard is
  the right instrument only when the invariant is inline control flow that no
  unit test can reach — not merely when writing one is inconvenient.
- **Expect to cap it, and document the residual.** At some point another
  missed shape is evidence the space cannot be closed syntactically, not a
  to-do. Record the known limits in the guard's own header, and be explicit
  that it is a backstop rather than the control — silence from it is not proof
  of safety.
- **Watch the cost.** That guard was belt-and-braces on an otherwise ~10-line
  fix and generated three of the loop's eight findings. Worth it here, on a
  money path; not worth it by default.

## Observability

- Failures reported (Sentry where appropriate)? Bulk operations expose what
  happened? Enough logging to debug a bad render/enrichment/job?

## Scope control

- Smallest coherent change for the approved plan? No speculative abstraction, no
  new external vendor, no scope creep beyond intent?

## Re-reviews (round 2 onward)

A code review is a loop too: you review, the author pushes fixes, you review
again. The planning contract's
[*Revise, discuss, and converge*](../ai-context/planning-contract.md#6-revise-discuss-and-converge)
section is the plan-side analog of this one; these are the code-side
invariants, and they are the engineering standard regardless of which agent is
reviewing:

1. **Re-inspect the current code.** An author's reply, explanation, or claimed
   fix is not evidence that the defect is gone. Read what the branch actually
   does now.
2. **Reconcile every specifically named prior finding** against the current
   branch. A finding is closed only when the engineering defect is absent — not
   because the thread received a response, and not because a commit message
   says it was fixed.
3. **Inspect related callers, invariants, and tests the fix could affect.** A
   local correction can introduce a regression outside the edited line.
4. **A regression introduced by the fix is a new finding**, weighted by the
   priority order above like any other.
5. **After more than one fix round, review the cumulative branch diff against
   the base branch**, not only the latest incremental commits. A fix in one
   file can break something that was part of the original diff and isn't
   re-shown in the newest commits — the diff is not the scope.
6. **A clean re-review is an empty findings list** on the structured defect
   pass surface (see below). Don't manufacture a finding to prove the round
   ran.

### The author's declines are where their error rate concentrates

Observed across seven rounds on PR #498 (20 findings, all confirmed, none
declined *as findings*): the author's error rate was not uniform across the
diff. It concentrated in the replies that said **"confirmed, but I resolved it
differently, and here is why."**

Both round-1 substitutions in that PR were incomplete, and one rested on a
factual premise the author had never checked — an objection about process
restarts that turned out to be irrelevant, because the job state it worried
about did not survive a restart either. The recommendation being declined was
correct; the reasoning for declining it was not.

**Two consequences, one for each side of the loop.**

*As the reviewer:* when the author accepts a finding but substitutes their own
remedy, re-review the substitution at least as hard as you reviewed the
original defect — it is newly written, un-reviewed code justified by an
argument you have not checked. "Agreed, fixed differently" is not convergence.

*As the author:* a decline is the one reply where you are reasoning rather than
reporting, so state the premise it rests on explicitly, and **verify that
premise before posting** rather than after. If the premise is about how the
code behaves, read the code; if it is about what a construct does, run a
three-line probe. The cheapest tell that a decline is unsafe is that its
justification contains a claim you have not executed.

Who posts the re-review trigger, which findings it names, who replies on which
thread, and the git mechanics around all of it are the implementing agent's
ceremony — for Claude Code, `CLAUDE.md`'s *Watching the PRs I open*. This
section defines only the reviewer's substantive standard.

## Codex has two usage limits — a security-review bounce is NOT a code-review outage

**The fact (David, 2026-08-15), canonical here because it binds every agent
watching a PR, not just the one that hit it:**

The Codex connector meters **two independent things**:

| Limit | Capacity | What bouncing it means |
|---|---|---|
| **Security reviews** | Limited, and the one that actually bounces | Only that security reviews are unavailable |
| **General code reviews** | Effectively unlimited for this repo | — |

The connector's comment names its own scope:

> You have reached your Codex usage limits **for security reviews**. Please try again later.

**So the rule is: ignore that comment and request the code review.** Post
`@codex review` as normal. A security-limit bounce is never a reason to skip a
code review, defer one, treat a round as converged, or merge past it.

**Evidence, because this was previously written up from a bad inference.** On
PR #458 the security bounce landed at 22:42 and a **full code review with 8
findings arrived at 22:48**, with a second round of 7 at 22:59 — code review
was working the entire time the bounce was on screen. On PR #459 the identical
bounce produced no review at all, not because Codex was unavailable but
because the misreading meant nobody asked. The earlier PR #371 observation
(bounces while David's visible weekly quota showed ~98% remaining) fits the
same picture: that quota is the code-review pool, which stayed full while the
*security* limit bounced.

**A genuine code-review outage is a different animal** — a request that yields
**no code review**. Judge that on the absence of the code review alone: the
two limits are independent, so a security bounce can fire *during* a real
code-review outage, and testing for "no review **and** no bounce" would let
that unrelated comment mask the outage indefinitely. That case still exists,
and since 2026-08-17 it is a **development stop**, not a stakes-graded
proceed: **every PR in the standard loop gets a code review, and nothing
merges until it returns** (a prototype-phase change never enters the loop —
working-modes.md, *The prototype phase, per feature*).
How many rounds follow is the **two-review limit**'s
([`working-modes.md`](../ai-context/working-modes.md#the-two-review-limit-on-autonomous-iteration-david-2026-09-19)) on work it
bounds; nothing governs whether the first one has to come back. The Worth rule
per finding and the ship gate shape what is written *within* that bound — this
sentence used to hand them the length question itself, which is a different
question than either answers. So an agent that cannot get a
code review stops and says so loudly to David rather than proceeding on a
docs-only or low-criticality exemption — that exemption is retired. The retry
limit in the implementing agent's ceremony (for Claude Code,
`.claude/skills/pr-watch/SKILL.md`) governs how many times to re-ask before
escalating. A security-limit bounce does not qualify as an outage, and must
not be reported as one.

**The failure mode this exists to prevent is a reading error, not a tooling
gap** — the prior rule quoted the "for security reviews" wording verbatim and
still concluded the review was unavailable. See
[`known-failure-patterns.md`](../ai-context/known-failure-patterns.md)'s
*Reading a scoped limit message as a blanket outage*.

## A comparative claim has two directions, and only one gets tested

**Applies when writing a finding, a reply, or a header comment** — not to the
code under review. A claim of the form *X is stricter/earlier/safer than Y*
asserts **both** directions. The usual failure is to check the direction that
prompted the claim, find it holds, and ship the comparison.

**Three instances in one session (2026-08-17), across three PRs:**

| Claim | Direction checked | Direction that was false |
| --- | --- | --- |
| The node-less guard fallback is "stricter on force pushes" | It blocks the permitted lease push | It *allows* `git-push -f`, which the parser blocks |
| `committedAt` "necessarily precedes the push"; backdating "only over-blocks" | Backdating moves the bound earlier | `GIT_COMMITTER_DATE` is arbitrary, so it can be set *forward* |
| The lease rule "sits behind GitHub's ruleset," unlike the fetcher rule | The ruleset exists and blocks force pushes | It targets `main`, not the `claude/*` branches the lease rule governs |

**Why it survives review of the code itself.** These claims live in prose, and
prose is not executed — nothing fails, and the half that *is* true makes the
sentence read as verified. The fallback claim had already survived one review
round, because that round only challenged the word "weaker" — and "stricter"
is equally one-directional.

**Avoid:** construct the counter-example for the opposite direction *before*
shipping the sentence, and prefer a **measured matrix to a comparative
adjective** whenever the behaviour has more than one axis. The git-constraints
section of `claude-core.md` carries a block/allow table precisely because two
successive adjectives were tried on the guard it then described and both were
false; a table has no direction to get backwards, and it survived the guard.

**The cheap test that would have caught all three:** ask *what would make the
opposite true, and can I run it?* Each was falsifiable in under a minute —
hiding `node` from `PATH`, setting `GIT_COMMITTER_DATE` to a future date,
checking the ruleset's *target* rather than its existence. None was hard to
check; all three were simply never checked.

**Note which clock that middle one names, because the first version of this
line got it wrong.** It said "reading `git commit --date`" — but `--date`
overrides the **author** date, and the claim under test was about the
**committer** date. Measured in a scratch repo:

```
git commit --date=2001-01-01 ...              author: 2001   committer: now
GIT_COMMITTER_DATE=2031-01-01T00:00:00Z ...   author: now    committer: 2031
```

**The committer form needs the full timestamp; the author form does not.**
`GIT_COMMITTER_DATE=2031-01-01` fails with `fatal: invalid date format`
(git 2.43), while `--date=2001-01-01` is accepted. An earlier version of this
block abbreviated both, so the line a reader would copy errored out — and it
survived review because its neighbour, which tolerates the short form, sits
directly above it. Presenting an abbreviated command as "the measurement" when
the abbreviation is not what was run is the same defect as the rest of this
entry, one layer down. (Codex, #506.)

So a reviewer following the original recipe would have checked a clock the
claim never depended on, found nothing, and concluded it held. **A remedy that
does not exercise the thing it is prescribed for is worse than no remedy** —
it converts "unverified" into "verified" while changing nothing. That this
happened *inside the entry about testing claims properly* is the strongest
argument it makes. (Codex, #506 round 2.)

**A near miss that does NOT belong here**, recorded because it was in this
list for one review round: a `Math.min` over a widened set, described with the
wrong causal mechanism. That has no opposite direction — "the reduction was
wrong" and "its consumer is the ordering check" are unrelated predicates, not
two halves of a comparison, and the counter-example test above would not have
caught it. Its actual lesson is *trace a value through its consumers*, and it
lives in
[`reduction-over-a-set-that-changed-size.md`](../../.agents/memory/reduction-over-a-set-that-changed-size.md).
Padding a pattern with an adjacent-looking case makes its mechanism claim
false, which is the same defect as the pattern itself. (Codex, #506 round 1.)

## A count in prose is a hand-maintained duplicate of the thing it counts

**Applies to a number that summarizes a separately-maintained enumerated
set** — "four findings", "five failed attempts", "three removed outright."
The number duplicates an enumeration that lives somewhere else, so it is a
[duplicate source of truth](../ai-context/known-failure-patterns.md) in
miniature — and the copy is the one that rots.

**Does not apply to a standalone scalar with no enumeration behind it** — a
configured limit, a threshold, a date, or a count read directly from a
canonical, mechanically-produced source ("236 tests" straight from the test
runner's own summary line has nothing to enumerate against; it either matches
the runner's current output or it doesn't). Telling a reviewer to "enumerate
or delete" a value like that would be asking them to invent an enumeration
that was never the source of truth in the first place. The distinction is
whether some other artifact enumerates the members this number is counting —
if yes, this pattern applies; if the number **is** the artifact, it doesn't.

**What makes it worse than an ordinary stale claim:** it goes stale *during the
edit that is fixing something else*, so the moment of highest attention is also
the moment it breaks. Three instances in one session (2026-08-17):

| Where | What happened |
| --- | --- |
| A guard header's job list | "one job" → "FIRST/SECOND", which read as exhaustive and omitted `checkCommand`'s standing refusals |
| A harvest entry's instance table | "four instances" survived removing one of them, and the count was load-bearing in the argument for the entry existing |
| A contract section's header | changed to "five failed attempts" over a body still enumerating three and saying "four definitions" |

The third is the sharpest: it happened **inside the edit that added the fifth
attempt**, in a section whose subject is claims going stale.

**Avoid — in order of preference:**

1. **Enumerate instead of counting.** A numbered list cannot disagree with
   itself; a sentence saying "four" above a list of three can and did.
2. **Derive the number mechanically** if it must appear (a script, a test).
3. **Delete it.** "Several rounds" carries the same weight and cannot be wrong.

**Never patch the number.** Editing "four" to "five" and moving on is what
produced instance three — the count was corrected and the body it summarized
was not, so the paragraph was internally inconsistent in a *new* way.

**Graduation trigger.** Three recurrences in one session makes a deterministic
check a named candidate under this repo's recurring-failure→CI-guard rule.
That's a code change, so it's tracked as a proper backlog item —
[`deferred-work.md`](deferred-work.md#code-level-tech-debt) — rather than
left to whoever next re-reads this paragraph during a maintenance sweep.

## A boundary that resists repeated definition is missing a decision, not a better sentence

**Looks like:** you write a rule that needs a general test to sort cases, a
reviewer breaks the test with a counter-example, you sharpen it, and the
sharpened version breaks somewhere else. The instinct each time is that the
sentence was not precise enough.

**PR #504 is the worked example: five definitions of one boundary failed in
sequence**, each refuted by a concrete counter-example, while the behaviour
underneath never changed. The enumeration and what each attempt got wrong are
in `CLAUDE.md`'s *Model, cost, and routing*, under the rule that an
unclassified judgement does not dispatch — not repeated here, since the
instance belongs to that contract and only the generalization belongs in shared
review practice.

**What actually ended it was two things arriving together, and neither was a
better sentence:** an owner resolving what a dispatched assessment is *worth*,
and that same owner separately instructing that the boundary stop being
defined at all. The first fact alone didn't stop the drafting — it was
immediately spent deriving a sixth attempt, in the same breath as recording
the fifth having failed. It took the explicit stop instruction, on top of the
new fact, to actually end the cycle. A generalization that keeps only the
first condition would predict that the fact alone should have been enough,
which is the opposite of what happened.

**Two consequences worth having in front of you during a review loop:**

- **Count the attempts.** Repeated failed definitions of the same boundary —
  not a specific number; the worked example ran to five with nothing
  stopping it at three or four — is the signal to stop drafting and go find
  the missing decision. It is cheap to count and easy to miss, because each
  individual attempt feels like progress.
- **Once the decision arrives, the temptation is to spend it on one more
  definition.** That is exactly what happened on #504: the new fact was used to
  derive attempt five, in the same commit that recorded four having failed.
  The decision's value is usually that it makes the definition *unnecessary*,
  not that it makes one possible.

**A reviewer is well placed to say this out loud**, often better placed than
the author — the counter-examples are coming from the reviewer's side, so it
sees the sequence before the author admits it is one.

## Review output format

**Two delivery surfaces exist; they don't support the same shape.** This split
is the code side's own. It used to be described as shared with the plan-review
contract, which had the same two surfaces; the 2026-09-18 planning redesign left
the plan side with one prose surface and no status label, so there is no longer a
twin to point at. Nothing about the code surfaces changed. Names for the two, used
throughout this doc: a **full assessment** (one complete document, with a
status label) and a **structured defect pass** (diff-anchored findings only, no
status label). Naming them is terminology, not permission to weaken either —
the expectations on each surface are unchanged.

### Full assessment — full-document delivery (a human reviewer, or an agent free to post one document)

Produce concise, prioritized feedback. Label overall status (no approval
language) — e.g. *No major technical disagreement · Directionally good, revisions
needed · Substantive technical concerns · Strong disagreement on direction · Human
clarification required · Repo context required.* For each finding: what, why (tied
to a priority above), and a concrete suggestion. Separate **must-fix** from
**nice-to-have**. Escalate product and behaviour calls — anything that would
change intended behaviour or accept a user-facing shortfall — to David rather
than deciding them; a purely technical design fork is settled inside the loop.

### Structured defect pass — GitHub structured review (the `@codex review` transport)

A confirmed limitation of this transport, and the code side's own to carry now
that the planning contract describes a single prose surface: this surface has no
freestanding top-level write-up, only diff-anchored inline findings, and no
status-label or ledger channel. Don't ask this surface for the full-document
shape above — it can't post it. Each finding is its own inline comment,
anchored to the relevant line (or, for an oracle-driven finding with no single
line — a dropped requirement, a touched must-not-change area — the most
defensible nearby line). A clean round is an empty findings list; on a diff
this is stronger evidence than on a plan (compiling, passing tests, and CI back
it up), so — unlike the plan contract — silence here is a real, sufficient
result, not a transport limitation to work around.

(The product's plan-review skill defines the full plan-review format; this
section is the code-review analog.)

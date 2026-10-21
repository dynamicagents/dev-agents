---
name: security-audit-discovery
description: >-
  Go looking for the security weakness no single component owns: a sequencing or
  interactivity weakness that parts of the Dynamic Agents train, each plausible on its
  own, compose into. Works from a brief carrying the severity floor and the recent
  attempt history, researches attack hypotheses, has bounded investigators test them,
  confirms the evidence itself, files each confirmed finding as a private GitHub security
  advisory in the repository that owns the code, and writes one report per run. Discovery
  only: it writes no fix, no dependency bump and no pull request. Use when asked to audit
  the product, a repo or an area for security, or to go looking for vulnerabilities. Not
  for reviewing the pending diff on a branch (that is `security-review`), not for writing
  the fix, and not for a finding that is not a security weakness.
disable-model-invocation: true
---

# Security audit discovery

The unit of work is an **attempt**: a named hypothesis about what happens when parts of
the train are composed, tested against the code until it is confirmed or dropped. Not a
pass over a file list.

What a run is looking for is the weakness **no component owns**. An ordering nobody
checked, a retry that outlives the decision that stopped it, trust established once and
reused after the thing it was established about moved, a limit enforced on one path and
not on the second one, one tenant's input reaching another tenant's object. Each part
reads as correct on its own, which is exactly why reading one part at a time does not find
these, and why a depth-first sweep of every file is the wrong shape: a single-component
bug is what review and `security-review` already cover.

Triggered by a person, or by the Coordinator on a person's behalf. Nothing schedules it.

The workspace `AGENTS.md`, under "Discovery runs", carries the evidence gate, the ranking
axes, the disposition table, the citation rule, the cap and the rules against edits and
against reading a credential. Read it first; this file carries what is specific to a
vulnerability.

**A finding and the report never mix.** A finding is private and lives as a security
advisory in the repository that owns the code. The report is reached by a bearer link, and
says what was attempted and nothing a reader could act on.

---

## 1. The brief

A run holds no state between runs. Everything it knows about earlier attempts arrives in
the prompt that starts it:

```yaml
min_severity: high       # the floor. Step 7
history: |               # the rolling table from the most recent report, verbatim
  <the table, or absent>
history_state: complete  # complete, incomplete or reconstructed
prior_reports: []        # at most four unexpired report ids: detail, not the table
deadline: <ISO-8601 UTC> # optional. Absent means the run computes its own in step 2
```

**The run reads history from the brief and from nowhere else.** It calls no artifact API.
A Claude Code session on a laptop or in a container has no artifact read or write at all,
so whatever the brief did not carry is history this run does not have, and the report says
so rather than working around it. Where a run is hosted, and how its report reaches the
next one, is the caller's business and not this skill's.

- **Absent history is not evidence of novelty.** An attempt the window does not show is
  unknown, not new. Say which it is, and never present a thin window as a clean one.
- `prior_reports` is the detail behind the table, opened only when it would change what
  this run does, and only where the runtime can actually read one. A local session cannot:
  it says so and works from the table.
- `min_severity` arrives as `high`. Only an explicit instruction in this brief lowers it,
  in words, and step 7 is where that is binding.

---

## 2. One clock, shared

Take the run's timestamp and its deadline once, at the start, in UTC. The deadline goes
verbatim into every brief this run hands out: two workers must never disagree about when
to stop. The timestamp is this run's id and stays with the orchestrating run: a worker
files nothing, so it has no use for one.

```bash
date -u +%Y-%m-%dT%H:%M:%SZ                                 # Audit-Run: this run's id, to the second
date -u -d '+<window_minutes> minutes' +%Y-%m-%dT%H:%M:%SZ  # the deadline, if the brief named none
```

```yaml
# The run's one clock. Minutes, UTC, computed once and shared verbatim. `window_minutes`
# is where the deadline above comes from, and the only place that number is written.
window_minutes: 90        # the start of research to the deadline
open_candidates_until: 25 # minutes before the deadline: no candidate is opened after it
confirm_until: 15         # minutes before the deadline: confirmation stops here
```

The clock bounds **search and confirmation, and nothing after them**. Filing a confirmed
finding, writing the report and handing the session back all complete after the deadline
has passed: a clock that could stop a confirmed finding from reaching its advisory would
throw away work already paid for, and leave a vulnerability unreported to save minutes.

A deadline is **never** a reason to drop the floor, weaken the evidence bar or file a
candidate that is not confirmed. Running out of time means a run with fewer findings, and
the report says where the clock bit.

---

## 3. Check the credential before spending the window

Probe the advisory routes this run depends on **before** researching anything. The submit
probe creates nothing, because the body is missing a required field. A `422` is the green
light: the endpoint accepted the caller and rejected the body. A `403` means the credential
lacks the permission.

```bash
# Submit path, per candidate destination repository. `repository_advisories=write`.
echo '{}' | gh api -i --method POST repos/dynamicagents/<repo>/security-advisories/reports --input -

# Read path, the same repositories. `repository_advisories=read`.
gh api -i "repos/dynamicagents/<repo>/security-advisories?per_page=1"
```

`-i` is load-bearing: without it `gh` prints the body and the status and swallows the
response headers, and `X-Accepted-Github-Permissions`, the permission GitHub says the
endpoint wanted, is the only thing that separates a missing permission from a missing
role.

**A refused route stops the run for that repository**, and **every route refused stops the
run**: there is then nothing this session could do with a finding, and researching one
anyway produces a vulnerability with nowhere private to put it. Report which endpoint
refused and what that header asked for, say that a session's credential is not the Worker's
`GITHUB_TOKEN` binding (separate paths, so a scope granted to the deployment does not
reach a CLI session), and ask for it to be fixed. Do not audit on in the hope it clears,
and do not look for another way to publish what you find.

The read matters as much as the write. Without the listing, step 9 cannot run, and a
finding filed with no history behind it is how a decision somebody already made gets
re-filed. So a candidate owned by a repository whose listing is refused is handed back with
its prepared body, never filed blind.

A repository with no advisories answers the listing with `200` and an empty array, so
**`403` and `404` are both refusals here** and neither is an empty history: GitHub answers
`404` where saying "forbidden" would itself disclose something.

Capability is read from status codes only. **Never read, echo, log or copy a credential.**

---

## 4. Form the hypotheses

**Read the constraints first.** Each repository's `AGENTS.md` states what must not be
weakened: core's zero-trust constraints, `g2a-protocol`'s rules for the wire, starter's
cancellation invariant and its isolation check. A constraint stated that plainly is rarely
broken head-on. It is composed around, and that is where to look.

A hypothesis names **what composes with what, in what order, and what the attacker gets**.
Two things that are each correct, in a sequence nobody checked. A candidate that names one
component and one bad input is a single-component bug and belongs to review.

The seams this train has, as prose rather than paths, because a path into a submodule does
not resolve from every checkout:

- **The gatekeeper crossing**: minted tokens, claims and audience, the push callback and
  its validation token, the questions a human answers and the answers coming back.
- **The durable task lifecycle**: accept, cancel, retry, idempotency, settle, the delivery
  outbox, retention, and the guarded writes that decide each.
- **Delegation**: a step job, a subagent, what a child may read and what it leaves behind.
- **The capability surfaces**: the egress gateway and the stream parser, the container and
  its install, token placeholders and the swap that replaces them.
- **The deployment**: bindings, migrations, the secret surface, per-tenant isolation inside
  one bundle.
- **The scaffold**: what a new project inherits before any of this is installed.
- **Publishing**: OIDC release, a git ref installed by `prepare`, which scripts a consumer
  allows to run.

Interaction classes worth asking about, because this is the shape such weaknesses have
had: a decision read before the write that decides it; a retry that survives a terminal
state; a cancel racing a settle; a resume carrying state from before an authorization
changed; a callback target an attacker can influence; a surface reachable only after a
tool call; trust pinned once and reused after its subject moved.

### The hypothesis phrase

Each attempt gets a short readable phrase naming the interaction, and it is the name that
attempt keeps: the first column of the report table, and the stable key a later run
recognises it by.

**Mechanism vocabulary only.** The phrase says what composes with what and in what order.
It never names a repository, a module, a file or a line. The report is reached by a bearer
link, so a phrase saying where the weakness is localises it for anybody holding that link.
`references/run-report.md` carries the rule, and the case where a phrase cannot be written
without a location.

**Novelty is a judgment, not a key.** Hold the phrase against the supplied table and ask
whether that attempt has been made: the same interaction under different words is a
repeat, a different sequence or different parties is new. No taxonomy, no hash, no
mechanical key, and no pretending that history nobody handed you proves anything.

---

## 5. Investigate with bounded subagents

Fan out over candidates, never over the product. One investigator takes one candidate, and
its brief stands on its own: a skill with `disable-model-invocation: true` is not preloaded
into a subagent (`AGENTS.md`, under "The prompt names the skill"), so nothing in the brief
may assume the subagent can read this file.

A worker brief carries the hypothesis phrase, what to read and which sequence to establish,
the run's deadline verbatim, the evidence bar from step 6, and the rules it works under:
change nothing, file nothing, publish nothing, and never read, echo, log or copy a
credential. Filing is the orchestrating run's alone.

**Concurrency stays modest.** No more than three investigations in flight, because every
claim that comes back has to be verified by the run itself, and that verification is the
narrow part. More workers buys queued claims, not findings.

**Depth, not more workers.** A candidate still unresolved after it has been read carefully
is Supported and drops out of filing. A second investigator on it buys a second opinion,
which is not evidence.

Stop opening candidates at `open_candidates_until`, and stop as well on reaching the cap
in step 8: there is nothing further a candidate could be filed as.

---

## 6. The run verifies, the worker does not

A subagent's report is a **claim**, and a claim is not evidence. Before a candidate can be
filed, the orchestrating run re-reads the code at `HEAD` itself and re-runs whatever the
claim rests on, naming the commit it read.

What makes a vulnerability **Confirmed** here is a reachable sequence the run has walked:

- the **entry point** it starts from: a route, an A2A call, a gatekeeper claim, a tool the
  model can call, a file the container writes, an environment a `postinstall` reads;
- **each hop**, as a full-SHA permalink with a line range;
- **the composition**: why those hops hold in that order, and what the ordering costs;
- **what the attacker gets** at the end of it, and who is exposed;
- where the sequence can be driven, the command and its output.

"This looks unvalidated", a sequence that holds only under an assumption nobody can check,
and a hop the run could not reproduce are all **Supported**: reported to the invoking
agent, filed nowhere, however large the stated impact. Impact never promotes a class.

Stop confirming at `confirm_until`. A candidate still unconfirmed when the clock reaches it
is Supported, and the report says the clock decided it.

---

## 7. Severity, and the floor

One fixed rubric, in GitHub's own vocabulary, so the value written on an advisory is read
off a table rather than argued per finding:

| severity | what it takes |
| -------- | ------------- |
| `critical` | an unauthenticated attacker crosses the boundary the train is built on: gatekeeper trust forged or replayed and accepted, a signing key or tenant secret exposed, attacker code reaching a deployed Worker or a container holding the repository's credentials |
| `high` | a reachable party crosses a boundary it is not inside: one tenant's data or egress reached from another, a durable task's integrity broken, a credential or its placeholder leaving the path it was swapped onto |
| `medium` | reach stops inside one tenant, or the sequence needs a precondition the attacker does not control: a limit enforced on one path and not the second, a surface that opens only after an operator acts |
| `low` | hardening with no path behind it: a defence in depth missing where another one still holds |

**The floor is `min_severity`, and it starts at `high`.** It is lowered **only** by an
explicit instruction from the invoking agent, in words, in the brief. Nothing else lowers
it: not a run that has found nothing, not absent history, not an approaching deadline, not
a cap with room left in it. A run ending with nothing at or above the floor files nothing
and says so, which is a normal outcome.

A candidate below the floor is handed to the invoking agent like a Supported one and filed
nowhere. The report carries the floor that was in force, which is a property of the run and
never the severity of a finding.

---

## 8. Order, and at most three

Severity first, descending. Then `AGENTS.md`'s axes as tie-breakers, in that order: reach,
the cost of leaving it, the cost of doing it, each answered with evidence rather than an
adjective.

Then the cap, which is `AGENTS.md`'s: at most three filed, and **never a target**. No
search widened to fill it, no weaker candidate promoted into it, no floor lowered to reach
it. A confirmed finding past the cap
goes to the invoking agent in the session's report; if it is lost with the session the next
run rediscovers it, and that is the designed safety net rather than a leak.

---

## 9. Before filing: what has already been decided

Per owning repository, read the advisories already there with the `state` filter left off,
which is every state this caller can see. Then apply the disposition table in `AGENTS.md`,
under "What earlier runs and earlier people already decided": its rows are keyed on the
decision a record carries and it names the advisory state that spells each, so there is
nothing to translate here. Read the code at `HEAD` again as well, because a prior reason is
evidence about the past rather than about today.

Two limits to state rather than paper over. An advisory a maintainer drafted alone, without
this identity on it, is invisible to the listing. And the supplied table says what was
**attempted** while the advisories say what was **filed**: neither is the other's index, so
say which of the two answered a question.

The exact calls, with the permission each needs, are in `references/advisory-api.md`.

---

## 10. File each finding as a private advisory

Read the owning repository's `SECURITY.md` first and follow it; it is authoritative for its
own route. Today each one points at GitHub's private vulnerability reporting.

Advisory body:

```markdown
## Impact
What an attacker gets, and who is exposed.

## Where
The code the finding is about, as `repo/path/to/file.ts:line`.

## Evidence
The entry point, each hop as a permalink, the sequence that composes them, and what was
read or run. Enough for a maintainer to re-run the check.

## Suggested direction
Where a fix would go. Not a patch: this run does not write one.

Audit-Run: <the run's UTC timestamp from step 2>
Audit-Hypothesis: <the phrase this attempt is named by>
```

`severity` takes one value from the rubric in step 7, and it is `severity` **or**
`cvss_vector_string`, never both: the API rejects a body carrying both.

**`Audit-Run` is the join, and the only one.** The same timestamp appears on every advisory
this run files and on this run's rows in the report table, and nothing else ties the two
together: the report carries no GHSA id, no repository and no path, and the advisory carries
no link to a bearer-link artifact. `Audit-Hypothesis` repeats the phrase, which is what lets
a later run rebuild the rows that filed once the report that carried the table has expired
(`references/run-report.md`, "When the table cannot be recovered").

**No key, and no hash.** A truncated hash of a repository, a path and a finding class is a
short value over a small space: anybody holding the report can enumerate that space and
recover what the value points at, so it is not a safe pointer in an artifact a bearer link
opens. A second hash invented for the advisory store alone would be a key nothing checks,
which is the other way a dedup key goes wrong. Dedup here is step 9, and it is read rather
than computed.

Then read the advisory back by its `ghsa_id` and confirm it is there. A refusal at any of
these steps stops the run as in step 3: the prepared request body goes to
`/tmp/security-audit-handoff/`, the operator gets the exact status and the UI route, and
nothing is published anywhere. **Outside the repository** is the requirement and `/tmp` is
how it is met: a path inside the checkout is one `git add -A` away from being the public
disclosure this step exists to avoid, and the handoff only has to outlive the session the
operator is reading.

If the invoking agent asked for report-back-only, file nothing and hand the finding back
instead. That is the only case in which a confirmed finding is not filed.

---

## 11. Write one report

One report per run, human- and agent-readable, written once at the end. Its contract, the
rolling table, what it may never carry and how history ages out are in
`references/run-report.md`.

The run **produces** the report and writes it to `/tmp/security-audit-handoff/report.md`,
then hands the text back in the session report. Publishing it where a next run can be
briefed from it belongs to whoever hosts the run, and a local session says plainly that it
published nothing.

---

## 12. Report back

To the invoking agent, in the session: every hypothesis attempted and what happened to each;
each filed finding with its advisory URL; each Supported candidate and what stopped it; each
candidate below the floor; the floor in force and who set it; where the clock bit; what the
brief did not carry and what that leaves unknown; anything the advisory listing could not
see; and the report text with its path.

---

<!-- guardrail:start -->
- **Report only.** No fixes, no refactors, no dependency, lockfile or version changes,
  no submodule pointer bumps. Each needs separate explicit authorization from the
  invoking agent.
- Findings go to a **private advisory in the owning repository** by default.
  Report-back-only happens when, and only when, the invoking agent asks for it.
- **Never a public issue**, pull request, commit message, discussion or gist containing
  vulnerability detail. If the advisory route is refused, the run stops, hands the
  prepared body to the operator outside the repository, and asks. It never degrades to
  anything public.
- **Only a Confirmed finding is filed, and impact never promotes a class.** A candidate
  the run has not walked itself, or that rests on a worker's claim, is reported to the
  invoking agent and filed nowhere.
- **At most three findings are filed in a run**, and the cap is never a target: a run
  that found fewer says so, and no search is widened to fill it.
- **`min_severity` starts at `high`, and only an explicit instruction from the invoking
  agent lowers it.** Never an empty run, absent history, a deadline or an unfilled cap.
- **One report per run**, describing that run only. Never a tracking artifact, never an
  omnibus thread, never an edit to a report already handed over.
- The skill **never closes, reopens, edits or comments** on an issue or an advisory.
  Closing is the owner's. History is never filtered by state.
- The report carries what was attempted and nothing else: **no exploit evidence, no
  affected repository, component or path, no GHSA ids, no advisory links, no severities,
  no CWEs, and no detail a reader could act on**. The one severity word it does carry is
  the floor in force, which is a property of the run and not of any finding (step 7).
- **Never read, echo, log or copy a credential.** Capability is established by response
  codes alone.
- The run's own writes are limited to: an advisory report per confirmed finding, the
  report it hands back, and files under `/tmp/security-audit-handoff/`.
<!-- guardrail:end -->

## References

- `references/advisory-api.md`: the advisory calls, the permission and role each needs,
  which credential answered, and what an advisory cannot carry.
- `references/run-report.md`: the report's contract, the rolling table and its fixed status
  vocabulary, what a report may never contain and how to check that mechanically, and what
  survives when an artifact expires.

# The line: how a bead moves in practice

yardr builds no line in: stages, groups, routes and a flow compose one.
This page follows a bead down the line yardr itself is built with
(depot yardr, as of 2026-10-03). Its flows are in [flows.md](flows.md#worked-example-depot-yardr). A second
line takes the same work through a pull request on GitHub:
[the public line](#the-public-line).

```
small, specified: backlog ──pick──▶ siding ──folded──▶ ready ──release by hand──▶ new
small, shaped:                    shape ──small──▶ siding
backlog ──pick──▶ shape ──shaper──▶ new ──builder──▶ review ──▶ review-security ──▶ approved ──assembly──▶ merged on main
   ▲                       ▲                 │              │                 │
   │                       └──── changes ────┴──────────────┘                 │
   │                       └──────────────── red check or conflict ───────────┘
   ├──────── siding, ready to backlog by hand
   └──────── decide (Christopher) ◀── a question from backlog, shape, new, review, review-security or approved
```

## 1. Backlog and shape: the bead gets specified

New ideas land in stage `backlog`, routed to the manual group `backlog`. The
yardmaster (see [crew.md](crew.md), prompt the default pack's
`~/.yardr/packs/<pack>/roles/yardmaster.md`) or a person picks each one for
`shape`; the pick stays a person's, never a route. A bead already specified
well enough for a builder to finish it without asking skips that step and
goes straight on: a small one to `siding`, any other to `new`. The
yardmaster advances it by hand: to `siding` for a small one
(`yardr bead advance <id> --to siding`), or to `new` for any other
(`yardr bead advance <id> --to new`); Christopher can do the same from
`yardr review -g backlog`.

In `shape`, a shaper reads the bead and the code it names, and specifies it
until a builder could finish it without asking: a goal, where to look, what
"done" means and how to test it. Large beads are split, and
`yardr dep add` orders them: a bead is only ready once its blockers are
closed, or a staged edge releases it
early ([Dependencies](#dependencies)). A bead shaped at `difficulty:1` and
`size:small` goes to `siding` on `small`, to wait for company and leave
folded with it; any other `difficulty:1` bead goes to `new` on `done`; a
heavier one, a duplicate, or one needing a decision only a person can make
goes to `decide` on `question`, with the question asked on the bead first.

Small beads wait in `siding` for company, and leave folded into one carrier
([Folding beads](#folding-beads)), which waits in `ready` for a person to
send it to `new`. A bead in `siding` or `ready` that needs reshaping goes
back to `backlog`, by hand.

### Cycles of blockers

`yardr dep add` refuses a `blocks` edge that would close a cycle, and names
it in order, the new edge first: `yardr-a blocks yardr-b blocks yardr-c
blocks yardr-a`. An open cycle leaves no bead ready, and nothing would say
why. The child's edge that `dep add -k parent` adds ([Trains](#trains)) is
refused the same way; edges of any other kind (`related`, ...) decide no
readiness and are never refused for it. Closed beads count: a closed blocker
blocks nothing, but reopening it would make the cycle live, and `bead
reopen` does not look at edges. The refusal then says which beads of the
cycle are closed; `yardr dep rm` on the old edge makes room for the new one.

A store written before this check may hold a cycle. `yardr doctor` names
each cycle of open beads in a `cycle` line ([doctor.md](doctor.md)), and
`yardr dep rm <blocker> <bead>` on the edge that is wrong ends it. yardr
removes no edge itself.

## 2. New: a builder implements it

`new` is routed to `yardr-builders`: a herdr group running Claude Code with
`prompt=roles/builder.md` (read from the yard's home,
`~/.yardr/roles/builder.md`, since the depot keeps no role of its own),
at most 5 at a time. The daemon opens a worktree
on branch `yard/<bead>`, starts the agent in it and hands it a brief: the
role prompt, the bead, and the outcomes its stage offers.

Within a priority, the group takes the bead that entered the stage first:
the queue is stage-entry order, and priority still wins first. A bead sent
back to an earlier stage and returned queues again at the end, from when it
re-entered.

**How agents are attributed.** The agent runs in a herdr tab created with
its identity in the environment: `YARDR_ACTOR` (the agent's name,
`<bead>-<stage>`), `YARDR_BEAD`, `YARDR_SESSION`, `YARDR_STAGE`,
`YARDR_GROUP`, `YARDR_KIND`, `YARDR_MODEL`, `YARDR_GIT_SYSTEM_CLEAN`, `YARDR_HOME` and `YARDR_BIN`.
Nothing depends on the agent exporting anything: every event its `yardr`
commands log names it as actor.
Every move (`yardr bead done`, `advance`, `close`, `hold`, `release` and
`reopen`) also sends `YARDR_SESSION`, which the store checks against its
own session table: the id must be one the yard started, and the bead the
session was started for comes from that record, not from the caller. A
move of that bead is refused unless the session still owns it (`stale:
bead <id> is now in <stage> owned by <session>`), so an agent kept open,
or orphaned by a restart, after its bead moved on cannot end the session
that owns the bead now; nothing changes. Another bead moved from the same
pane (a follow-up the agent filed and advances) is checked as the actor's,
like a person at a shell, except that one owned by a live session is
refused rather than taken from under its agent. The store also knows the
pane itself: the runner records the pid of the tab's shell (for an exec
group, of its script) on the session, and a call whose process descends
from it is checked as that session whatever its environment says, so
unsetting `YARDR_SESSION` in the pane is not a way out, and naming another
session from it is refused. An agent whose commands run outside its pane
with another session's environment (Codex's shared background server) is
told apart by the worktree it runs in
([groups.md](groups.md#codex)). A person at a shell of their own has no
`YARDR_SESSION` and no pane the store knows, and is not checked. `yardr
review` sends the stage and revision the form showed instead: it refuses a
decision on a bead that moved or changed since. Every move takes
`--revision <rev>` for the same compare-and-swap, as BDP writes take
`If-Match`.

**Done waits for unread notes.** The daemon tells the session of a note
written for it once, when its agent is idle, but a note it never got to
tell still stands: the session's own `yardr bead done` is refused while a
note on the bead names that session and is not acked. The refusal lists
each unread note, with its number, writer and text, and how to ack it
(`yardr bead note <id> --ack <seq>`); after the ack the same done passes.
A person moving the bead is not gated, nor is a session of a runner with
no agent to ack (exec, manual, peer).

**Done waits for a clean worktree.** The session's own `yardr bead done`
is refused while the worktree its handle names has uncommitted changes.
The refusal names each changed file, with the three ways out: commit
them, remove them, or attach them to a note (`yardr bead note <id>
--file <path>`) and remove them; once the worktree reads clean the same
done passes. A person moving the bead is not gated, nor is a session
whose handle names no worktree.

The telling reaches the session whatever its pane shows. Where the pane
shows the prompt of its harness the telling is typed into it, as a crew
member's nudge is ([crew.md](crew.md#text-in-the-input)); where it shows
none, or none yardr can read (the harness idle at a prompt herdr cannot
see, a shell of its own, a kind whose marks are unknown), it goes through
`herdr agent prompt`, which herdr submits itself. The `note_told` event
says which way with `delivery` (`typed` or `agent prompt`). A telling
neither way takes is marked untold, with why, and the yardmaster hears it:
`note_untold` is of the class `attention`, and `yardr bead show` says
`could not be told: <why>` where it said `will be told`. One behind a
first prompt that was given up is marked untold too: the first prompt goes
first, and it never arrives. A note behind a first prompt that is stuck on
a screen that is not there does not wait behind it: through herdr it goes
at once.

An idle session with its bead still in its stage gets one prompt to hand
on before the idle limit counts, once per idle spell (`session_idle_nudge`).
One with no note of its own gets `your bead is still in <stage>: write your
note and hand on, or say what blocks you`; one whose own note already carries
its test line wrote everything but the outcome, so its nudge names the command:
`your note is on the bead; report the outcome: yardr bead done <id>`. A session
still in its stall window, one judged stalled, one with a first prompt still
unsubmitted, one with a note already due, and one whose own note carries no test
line are not nudged.

**A move refused to an agent is logged.** A move that works ends the
agent's session, so an agent whose `yardr bead done` was refused sits idle
with "done" as its last word, and the bead shows nothing of it. The store
therefore logs `move_refused` on the bead when it refuses `done`, `advance`,
`close`, `hold` or `release` to the agent of a session (the session the
move was checked as: the pane's, else the one `YARDR_SESSION` names):

| field | |
|---|---|
| `reason` | `stale` (the session no longer owns the bead, or the bead changed since `--revision`), `not_allowed` (the flow has no such move or outcome for the stage, or a part has no train), `not_member` (the stage's group has members and the agent is none), `not_found` (no such bead), `other` (anything else that failed the move: a flow that does not resolve, say) |
| `command` | the move as `yardr` words, with the bead as the agent named it: `yardr bead done <id> --outcome shipped` |
| `error` | what the agent was told |
| `session`, `agent`, `group`, `stage` | whose session it was and the stage it was started for |
| `session_bead` | the session's own bead, when the move named another |

It is on the bead the move named, or on the session's own for `not_found`,
and at most once per bead, session and reason, so an agent that retries
says it once. A person's or a crew member's refused command logs nothing (they
are in no session and read the error where they typed it), nor does a
manual group's claim. It is in a new crew member's default `--on`, so the
yardmaster hears it; `yardr inbox` leads its row with `reason`, `command` and
`error`.

What never reaches the store is not logged: a command `yardr` itself
refuses for its shape (`advance` without `--to`, a missing id, an unknown
flag), one that finds no server, and one the harness never ran (a
permission prompt it waits on, a hook that denied it). The first two print
their error in the pane, which `session_idle` carries as `tail`. A
permission prompt raises `session_blocked` when the agent's status turns
to it, and that event carries the end of the pane as `tail` too (its last
20 lines, as `session_stalled` and `session_harness_error` do): the
question the agent waits on is in `yardr inbox`, with no `herdr agent read`
to get it.

At startup, yardr answers only a folder-trust dialog named by the agent's
harness, while the first prompt is still pending and no delivery was taken.
A prompt seen in the pane or a working status closes that guard. Crew
sessions also read their `crew_status` history since the current
`crew_started`, so a daemon restart cannot reopen trust after the session
was seen working. A crew prompt counted sent but never taken is answered
all the same when the session never worked and the live pane has no echo
of it; `prompt_started`, a shown or typed prompt, or any working in the
session's history refuses (yardr-x9kv). An unknown dialog stays for a
person and is reported as `crew_blocked` (yardr-v3mp, yardr-9a82, yardr-q7rd).

The builder implements the change, commits on its branch (never pushes or
merges), runs the depot's test command on the last commit (`sh .yardr/test`
in its worktree, which its brief prints as `test:`: `gofmt`, `go vet`,
`go build`, then `go test` on the packages the branch changed and their
importers, without `-race`: the race detector runs at landing only, see
below), leaves a note with what it changed and verified, ending
in a test line (the command, the commit, the result with counts), and
reports `yardr bead done`, which the flow sends to `review`.

### The landing run, and the whole suite on a quiet machine

The landing run (`go test -race` on the selection plus the six
black-box suites, vet for linux too, and, beside it since yardr-9xd9,
the store, dispatch and bdp suites again over the socket when the plain
selection holds one of them; the socket step's output is printed when
the first has ended, and the run is red when either is) runs once per
bead, in the assembly, on exactly the commit that lands (section 4):
the assembly runs the same `.yardr/test` with `YARDR_LANDING=1`. The
whole suite (`go test -race` on every package) no longer gates each
bead: it runs on a quiet machine as a backstop
([testing.md](testing.md), R6), and where someone runs
`YARDR_LANDING=1` on the base itself. Until 5 Oct 2026 the whole suite
ran three times, for the builder, the reviewer and the assembly: about
16 of a bead's 37 minutes at the median. The builder now runs the
script plainly, and a reviewer runs it over its own commits or not at
all: not at all when the builder's test line names the commit under
review and the reviewer committed nothing, and otherwise with
`YARDR_BASE` set to the commit the last test line on the bead names (the
stage files of `review` and `review-security` say so, yardr-0cw8). The
script tests what changed since its base and whatever imports or reads
that, so the selection is the reviewer's commits alone, not the
builder's whole change again: a fix in a leaf package takes seconds. A
review base left behind by a rebase is compared from the commit it and
`HEAD` share, which lies before the tested commit: the run tests more,
never less. If the named base is ahead of
`HEAD`, the merge base is `HEAD` and would select nothing, so the script
says "cannot compare"; the reviewer then runs plainly from the session's
base. A base that is not in the repository at all also says "cannot
compare". On 22 Oct 2026 the reviewer's two runs
of one bead waited 1530 s and 1447 s of about 2000 s each on the lock, and
the security reviewer's run 1372 s, all to test the builder's whole change
again after a review fix (yardr-a7sd).

The landing run is also the only one with the race detector, besides the
quiet run's (since yardr-ghjv, 22 Oct 2026; [testing.md](testing.md), R4).
The builder's and the reviewer's plain run tests the same selection without
`-race`, and so takes no place in the race lock's queue for its race: of 170
passing test lines measured that day, 66% of the gate's wall time was spent
queued there. A plain run whose step covers the whole suite still queues on
it as class 1, behind landings ([testing.md](testing.md), R5).
A data race therefore shows at the landing, which sends the bead back, and
not in a builder's or a reviewer's run.

With `YARDR_LANDING=1` the script first asks what changed since
`YARDR_BASE`, as a plain run does; the assembly has just rebased the
branch onto the base, so that is what the landing adds. A landing that
changes code -- a `.go` file or a file a package embeds -- runs the
plain selection plus always the six suites that build the tree's
binary and drive it without importing the changed packages
(`contrib/assembly`, `contrib/peer`, `contrib/deploy`,
`contrib/server-yard`, `contrib/isolated-yard`, `contrib/release`:
[testing.md](testing.md), R5). A landing that changes nothing compiled
runs the plain selection alone (since yardr-bxh2, 13 Oct 2026:
gofmt, vet, build, and the tests of the packages the table names for
the changed files), and since yardr-57x5 (22 Oct 2026) without
`-race`: the race detector looks at compiled code and none changed, so
the run takes no place in the race lock's queue for its race either.
A plain run does the same, whatever it changed, unless its step covers
the whole suite, which queues as class 1 behind landings. A landing is
the whole suite when what
changed cannot be selected, or there is nothing to select from:

- `go.mod` or `go.sum`, which move every package;
- a file in no row of the table, which any test may read;
- deleted: what embedded a file that is gone cannot be asked any more;
- nothing changed at all, or the base is not there to compare with,
  which is how CI, a release and the quiet run on the base run it.

The first line of the output says which run it is and names the file
that decided it:

```text
test: YARDR_LANDING is set, and nothing compiled changed since main (YARDR_BASE), from 51c8a9e: testing without -race
test: docs/design/2026-10-12-yardr-nx54-outside-pr-review.md changed: read by the tests of .
test: testing, without -race, what changed, what imports it and what reads it: yardr.dev/yardr
```

A plain run says why it is not raced, whatever it changed, without the
landing's mark (`test: what changed since main (YARDR_BASE), from 51c8a9e:
testing without -race (race runs at landing only, docs/testing.md R4)`), and
makes no claim about it when it has nothing to test.

```text
test: YARDR_LANDING is set, and internal/store/beads.go changed since main (YARDR_BASE), from 51c8a9e: the selection plus the six black-box suites (contrib/assembly, contrib/peer, contrib/deploy, contrib/server-yard, contrib/isolated-yard, contrib/release)
test: the plain selection holds store: running the socket suites beside the first run
```

Such a landing is still tested as it lands: every program and every
test binary is built from the source the base has, and the base is
kept green by the quiet whole-suite run. Only a test that opens a
changed file by path can differ in a nothing-compiled landing, and
those run. What counts as compiled is a `.go` file (a test file too),
a file a package embeds, and a deleted file, which may have been
embedded and cannot be asked: those, `go.mod` and `go.sum`, and a file
no row knows keep `-race` at a landing. A run without it -- a plain run, or
a landing of nothing compiled -- judges no package's time
against the 60 s budget ([testing.md](testing.md), R1, which is defined
under `-race`); the sleep budget reads the tree and is judged as ever.
Before yardr-57x5 a design document waited 20 to 35 minutes on the race
lock to run one root-package test, in each of three rounds (yardr-5dzn).
On 12 Oct 2026 eleven of 66 landings were the whole suite
for one file under `docs/design/`, 66 minutes of the day's 298
([the design](design/2026-10-12-yardr-1vt3-landing-several-at-once.md),
section 3.1). When it goes wrong, a row of the table names too few
packages: the test that reads the changed file fails at the next
quiet whole-suite run, on a base that did not cause it, and the fix
is the row.

What the incremental landing costs is that some faults are found
later than the landing that caused them -- at the quiet run, with no
bead to send back -- instead of in the assembly. They are the faults
neither the selection nor the six can see:

- a test that reads a file by path, when the table in `.yardr/test`
  leaves its reader out. `go list` knows what a package imports and
  embeds, not what its tests open, so the script has a table of path
  to packages (the starter pack runs `internal/pack` and
  `internal/cli`, whose tests read it; `.yardr/flows/` runs the
  packages that read the repository's own flows), and a changed file
  that is neither Go, embedded nor in the table still runs every
  package. What is left is a row that names too few packages;
- store, dispatch or bdp behaviour over the unix socket that the
  gate skips: the socket leg runs at a landing only when the plain
  selection already holds one of the three, the same reach the plain
  run accepts everywhere else;
- a test in a package the branch neither changed nor is imported by,
  and none of the six, which fails for a reason no import shows
  (shared state on disk, timing under the load of the whole run).

A test that reaches code only by building the binary is no longer in
this list: the six always run at a code landing and exercise the new
binary. For the rest the builder previews the landing itself,
`YARDR_LANDING=1 sh .yardr/test` (step 3 of the builder's role),
which is the selection plus the six for a branch that changes
something compiled, as these do. An edit to `.yardr/test` on a branch
is tested by the builder's own run alone: the assembly runs the copy
`main` has. A reviewer's commits subject "review: <what>" get a
plain run too, over those commits alone, so a fault in one of them that
this run cannot see is the assembly's to find.

A red quiet run is told as `quiet_failed`, with each failing package's
output as a file; a run that names no failing package (a package over the
60 s budget under the strict R1 verdict, a vet or build error) carries the
end of its whole output as one file, `run.log`, so the verdict is there to
read and the suite need not run again to find it (yardr-4yqd).

The runs that race take one machine-wide lock at a time, and a landing
goes first in its queue (yardr-0cw8). The queue is a ticket for each
waiter in `~/.yardr/race.queue/`, named by its class, `0-` for a run with
`YARDR_LANDING` set (a landing, or the quiet run) and `1-` for any other,
then the time it arrived and its pid. The first live ticket may take the
lock, so landings are served before every other run, and each class in
the order it came. A landing is what frees the next bead of a chain: on
22 Oct 2026 an approved bead waited behind builders and reviewers on a
queue of six. Since yardr-ghjv only a run with `YARDR_LANDING` set has a
race leg, so this script makes class 0 tickets alone and the queue is
first come, first served; class 1 is left for the tickets of a copy of the
script from before it (a branch not yet rebased). The run that holds the
lock is never pre-empted, so a landing waits for it to end. `sh
.yardr/test --race-queue` shows the holder and the waiters in the order
they take the lock, each with its class (`landing` or `plain`).

How many landing runs go at once is the assembly group's `limit`:
every depot of this yard lands through one group
([configuration.md](configuration.md#tests)). A depot whose landing
is short may have an exec group of its own with the same script, so
that it does not wait behind a long one: this yard did so for
footplate on 12 Oct 2026 (`yardr group add footplate-assembly`, and a
route for stage `approved`, depot footplate).

### What the tests do not catch

The assembly runs the script as it is on the base, so a branch cannot change
what is run, but it runs in the branch's worktree, against the branch's code
and the branch's tests. A branch that deletes a test, skips it or makes it
trivially true passes vacuously. That is the accepted model for now: the
reviewer reads the diff and is the one who catches a weakened test, not the
script. The builder's run and the assembly's are the same in this.

## 3. Review: Codex reviews forward

`review` is routed to `yardr-reviewers`: Codex in the same worktree, with
`prompt=roles/reviewer.md` (how a reviewer works), read from the yard's
home (`~/.yardr/roles/reviewer.md`, since the depot keeps no role of its
own), and the stage file `.yardr/flows/default/review.md` (when each
outcome applies). It is the last review of whether the bead does what it
says, so it fixes what it can on the branch (commits subject
"review: <what>") rather than only reporting, tries the change,
runs the depot's test command if it committed (over its own commits, with
`YARDR_BASE` at the commit the last test line names) or the builder's test
line is not for the commit under review (the landing run is the assembly's),
and then:

- **approves**: a note with what it checked and fixed, then `yardr bead
  done` (to `review-security`) when the diff touches anything
  security-relevant, or `--outcome done-safe` (straight to `approved`)
  when it touches nothing on the stage file's list; in doubt it reports
  `done`;
- **sends back**: concrete findings, then `--outcome changes` (to `new`);
  the bead returns to
  the builders, in the same worktree. After two send-backs it holds the bead
  instead of a third, so the yardmaster looks;
- **asks**: a question only Christopher can answer goes to `decide`
  (`--outcome question`).

In a flow with a `merge` stage (section 5; depot yardr's has none), when a
merger sends a bead back for a `merge re-review`, the reviewer records
the old tip from the merger's note and runs
`git range-diff <base>...<old-tip> <base>...HEAD`. It checks only the
conflict-resolution changes: that both sides' intent was kept, the merger's
note names every conflicting file, and the test result is credible. It does
not redo the original feature review. If the resolution is sound, it notes
the range-diff and reports `done-safe` to go straight to `approved` if the
resolution touches nothing on the security list, or `done` to send it through
`review-security` if it does; otherwise it sends the bead to `new` or `decide`
with a concrete finding.

### Then once more, for security alone

A bead whose diff touches anything security-relevant is reviewed twice,
one review after the other (design
[yardr-ndv0](design/2026-10-12-yardr-ndv0-parallel-reviews.md), 12 Oct
2026). `review` asks whether the bead does what it says, is right and is
tested. `review-security` asks one other question of the same diff: what
does the change open, and to whom? Its stage file,
`.yardr/flows/default/review-security.md`, has the list: new callers, the
operator's checks, text from outside the yard, secrets, file modes,
listeners, dependencies. `review-security` is routed to `yardr-security`,
with `prompt=roles/review-security.md` read from the yard's home
(`~/.yardr/roles/review-security.md`, since the depot keeps no role of
its own): another agent asks it, with a brief of its own, because one
reviewer asked for everything reads for the feature first and for what it
opens last, with what attention is left.

The second review works as the first: it fixes a small finding on the
branch (commits subject "review: <what>") and then runs the depot's
test command, sends anything larger back to `new` with `changes` (the bead
then passes `review` again), and takes a question to `decide`. It is kept
from becoming a second
general review: a change that touches nothing on the list is passed with
one line saying so, and the tests are not run again for a branch it did not
change. A diff that touches nothing on the list goes straight from `review`
to `approved` on `done-safe`, and only beads the reviewer sends on with
`done` pass the second review. The two run one after the other and not at
once, so that both may commit on the one branch; the design has what a gate
for reviews at once would take.

The call between `done` and `done-safe` was the first reviewer's alone, by a
list in prose. The part of it that is paths is held by the yard now:
[`.yardr/security_paths`](../.yardr/security_paths) lists them (the store,
the socket API, the web view, hooks, peers and pairing, declared sources,
`go.mod` and `go.sum`, `.yardr/` and the assembly), and a `done-safe` for a
diff that touches one is refused, naming the files, so the reviewer reports
`done` and the bead goes on to `review-security`
([flows.md](flows.md#done-safe-and-the-security-paths)). The rest of the
list, which no path names (what the daemon runs as whom, a file's mode, text
from outside), is still the reviewer's to judge. The move by hand is held
too: an agent's `yardr bead advance <id> --to approved` from `review` takes
the edge `done-safe` takes, and is refused for the same diff with the same
message. A person's or a crew member's advance is not.

A bead the security stage makes another wait for (`yardr dep add`) holds
until it closes, and a bead's agent cannot close it. From an agent's session
pane, `yardr bead close` works on its own bead alone; any other is refused,
and so is an advance that moves another bead into a terminal stage. The
agent writes a note on that bead instead, and a person or the line closes
it. An agent cannot change a bead's type or depot either (`yardr bead
update --type`, `--depot`), on its own bead or another: the depot's
pointers pick the flow by them, so either could send its own bead by a flow
with no review, or walk a blocker past the stage its `--until` waits for.
What it files goes by the flow the yard picks, without a `flow` in its
metadata, into the flow's first stage or a stage people work (`decide`);
filed straight into `review` or `approved` it would skip the stages before.

## 4. Approved: the assembly lands it on main

yardr takes no position on how work lands: a PR per bead, a shared PR
several beads funnel into, or a direct merge. The assembly is not built in;
it is a composition. A stage (`approved`) is routed to an `exec` group whose
script does the landing, and `--limit 1` on the group makes it a serial merge
queue. yardr provides the mechanism and ships one reference script,
[`contrib/assembly/merge-local`](../contrib/assembly/merge-local); depot yardr
uses it to merge directly to `main`.

**The mechanism.** The exec runner starts the script in the depot with
everything it needs in its environment ([groups.md](groups.md#runners)):
`YARDR_BEAD`, `YARDR_DEPOT`, `YARDR_DEPOT_PATH`, `YARDR_BASE`, `YARDR_BRANCH`
(`yard/<bead>`), `YARDR_WORKTREE`, `YARDR_BIN` (this yardr), and
`YARDR_ACTOR` set to the group, and `YARDR_TEST`, the depot's test command
([configuration.md](configuration.md#tests)), unset for a depot with none.
yardr runs no test itself: whether the script tests before it lands, and
with what, is the script's. The script finishes by moving the bead, with a note:
`yardr bead advance "$YARDR_BEAD" --to <stage> --note -`. A script that
exits without advancing, closing or holding counts as a failed session, like
an agent that gives up, and after 3 of those the bead is held. Advancing ends
the session and the daemon stops the script, so it is the script's last step,
and the step before it is taking away what the script made and started: the
files of a test run, a directory it works in, the test command and everything
below it. A script stopped sooner, by TERM or INT, does the same before it
exits.

**merge-local.** For each bead it:

1. brings the base up to `YARDR_PUSH` where it names a remote, fast-forward
   only, so the branch is rebased onto the remote's commits and not a
   stale base; a base that diverged from the remote's branch reports
   `failed` with a note saying so, and is never merged or forced. It then
   rebases `yard/<bead>` onto the base in the bead's worktree, if the base
   moved; on a conflict it aborts the rebase and asks the flow what it
   allows (`prime --bead --json`) before it moves: the `conflict` outcome
   where the flow offers one (to `merge`, section 5), else the `merge`
   stage where the flow allows it, else `failed` back to `new`, as in
   depot yardr, whose flow has no `merge`. Only what the flow allows is
   tried, so no refused move is raised;
2. lowers the file size table of the depot's test command to the branch's
   files, where that command is one file of the branch that carries such a
   table (a line `filesizes='`; depot yardr's `.yardr/test` is one). It runs
   `sh <that file> sizes --rewrite` in the worktree, from the branch's own
   copy, since the branch's own table is what it rewrites; what judges the
   branch (step 3) stays the base's copy. Each row becomes the smaller of
   itself and its file's lines, a row whose file is gone or has at most 1000
   lines is deleted, and the change is amended into the branch's head, so a
   change that shrinks a listed file never edits its row and two that shrink
   neighbouring files cannot conflict on those lines
   ([testing.md](testing.md#file-size-budget)).
   A table already right is left alone, and the step is skipped for a wagon
   landing on its train's branch, since integrate-train lowers the rows once
   for the train ([below](#the-trains-own-flow)), and for a branch with no
   commit past the base, which has no head of its own to amend. The rewrite
   is bounded by `YARDR_REWRITE_TIMEOUT` (120 seconds unless set; if set, it
   must be a whole number of seconds, or the bead is held before the rewrite
   runs), with no race lock to credit, since it waits on none: at the deadline
   the run's whole process tree is killed. The bead is held when the rewrite
   outlasts its deadline, or fails, which says a row stands below its file
   (growth, or a row cut by hand, which no landing settles), with the last
   4000 bytes of what it printed in the note, and when it leaves anything but
   the table changed, stages a change, or moves the branch, the base or the
   worktree.
   Where the group's `cmd` sets `YARDR_LAND=squash`, the branch is then made
   one commit, written from the bead ([below](#landing-by-squash)); `rebase`
   is the default, and lands the branch's commits as they are;
3. keeps the machine's disk (`yardr disk keep`), then runs the depot's
   test command on exactly what will land, every time,
   including after a merger's rebase, with `YARDR_LANDING=1`, and records
   the commit it ran on. Under `disk_keep_gb` free the keeping rotates
   GOCACHE and clears stale go-tmp first ([setup.md](setup.md#the-machines-disk));
   a keeping that fails is in the log and the landing goes on to the tests.
   Where the command is the path of a file the base
   has (depot yardr's is `.yardr/test`), it runs the base's copy of that
   file, with `sh`, in the worktree; anything else is a command for
   `sh -c`. A depot with no test command lands untested, and the note says
   so. Red reports the outcome `failed` (to `new`; to `open` for a train),
   or advances to `new` in a flow without outcomes. The note starts with
   the branch, the commit the tests ran on, the base and what ran, and
   carries the last 200 lines of the output, so a test command should end a
   red run with the lines that say what failed. The builder reads it with
   `yardr prime --bead <id>`, which shows every note whole. A command that
   says it could not run at all (exit 2: a tool missing, a base it cannot
   find, a disk too full to start, as [the disk floor](testing.md#the-disk-floor)
   has it) holds the bead, since no builder can fix that. Nor can one fix a
   run ended by a signal from outside (exit 128+N; 143 is a `go test`
   killed with SIGTERM after every package printed `ok`): it is run once
   more on the same commit, after a note with the first run's output, and
   what the second run says counts; ended by a signal again, the bead is
   held with both outputs. The script's own kill at its deadline
   (`YARDR_TEST_TIMEOUT`, 1800 seconds besides what it waited for the race
   lock) is not that: it is a red run. The rewrite of step 2 has a deadline of
   its own, `YARDR_REWRITE_TIMEOUT`, and past it the bead is held. The
   tests start with no descriptor above 2 that the landing did not give them:
   merge-local closes what it inherited, and where its `sh` cannot name one
   above 9 (dash reads one digit as a redirection's number) it says which are
   open and exits 2, so the bead is held, rather than start the tests with it.
   The daemon keeps its own out of what it starts, so one that arrives is a
   leak to find. A branch that moved while the tests ran (a commit pushed to
   it meanwhile) reports `failed` the same way, with both commits in the
   note: nothing the tests did not see lands;
4. lands that commit, by its sha, by fast-forward only. Where the base is
   checked out it fast-forwards that checkout, only when it is clean; a
   dirty one is someone's work in progress, so the bead is held with a note
   saying so and the tree is never touched. Where the base is checked out
   nowhere it moves the ref alone (`git fetch . <sha>:<base>`), which works
   whatever state the depot's checkout is in: keep the base checked out
   nowhere and a dirty checkout never blocks the queue;
5. pushes the base if `YARDR_PUSH` names a remote (off by default, never
   forced). A failed push leaves the bead merged; the next landing's push
   carries it, and `YARDR_NOTIFY` (default the yard's `yardmaster` setting, else
   `yardmaster`) is mailed;
6. installs the landed build if the yard's `upgrade_from` setting names the
   bead's depot: it runs the installed yardr's `upgrade` and folds its
   one-line summary into the landing note, with the scripts the install
   refreshed by name, and its seconds into the log line.
   Like a failed push, a failed install where the yard still answers still
   merges, with a note saying what failed and what was put back; where the
   installed yardr predates the command the note says to install the new
   yardr once by hand first. When the install leaves the yard dead no
   advance is possible, and the bead fails its session toward a hold. A
   wagon never installs: it lands on its train's branch while the install
   builds the depot's checkout. The step activates only once the operator
   has installed the script and sets `upgrade_from`
   ([upgrade.md](upgrade.md#the-assembly-step));
7. advances to the terminal stage `merged` with the note `merged <sha>`,
   the net lines the landing added (`+<n> code, +<m> test`), what tested
   it, the seconds the tests took, and how the install went where it ran,
   which closes the bead; in a flow without `merged` it closes
   the bead with that reason. Before the outcome, this one or any other, a
   line of the group's log has the seconds of each step that ran:
   `== <bead> took: rebase 1 s, the tests 355 s, push 2 s, upgrade 24 s`.

It never forces, and a base that is not a local branch (`origin/main`) is
held: merge-local lands only on local branches.

### Landing by squash

A depot chooses how its beads land with one option in the assembly group's
`cmd`: `YARDR_LAND=rebase` (the default, so no depot changes until it opts
in) or `YARDR_LAND=squash`; any other value holds the bead before anything
moves. The starter pack makes its assembly group with the option set
(`env: { YARDR_LAND: squash }`,
[packs.md](packs.md#how-a-pack-maps-to-the-yard)), so a depot set up from it
lands by squash; a group that exists is never changed by the pack, and opts in
with `yardr group set <group> 'cmd=YARDR_LAND=squash <the rest of the cmd>'`.
In squash mode merge-local replaces the branch's commits with one,
between the lowering of the file size table (step 2) and the tests (step 3),
so that the lowered table is in it and the commit the tests run on is the
commit that is fast-forwarded onto the base (steps 3 and 4 as above). The
commit is made with `git commit-tree`, so the yard's commit-msg hook, which
would put its own trailers on it, never runs; the script writes them. It is a
[Conventional Commit](https://www.conventionalcommits.org/en/v1.0.0/) written
from the bead, with the bead's id as a trailing reference, as GitHub's
`(#123)`, and not as the scope:

```
<type>[(<scope>)][!]: <bead title> (<bead id>)

<the message of each commit on the branch since the base, oldest first,
each with its own trailers removed, separated by a blank line>

BREAKING CHANGE: <as a commit carried it>
Refs: <issue url>
Yardr-Bead: <bead id>
Yardr-Agent: <agent>
```

- **type**: the bead's label `kind:<type>` (`feat`, `fix`, `docs`,
  `refactor`, `test`, `perf` or `chore`; the yardmaster sets it with the
  estimate). With none, `fix` for a bead of type `bug` and `chore` for any
  other.
- **title**: the bead's, whole and never cut: a builder retitles the bead to
  say what the change does, in the imperative, and a reviewer checks that.
- **scope**: read from the diff, never chosen by a person or an agent: the
  last element of the deepest directory that holds every path the squash
  changes (a rename counts both its paths). None when that directory is the
  root, one of the top-level containers that say nothing (`internal`,
  `contrib`, `packs`, `cmd`, `pkg`, `src`, `lib`: a list at the top of the
  script, for a depot's copy to change), or the type itself (all of `docs/`
  gives `docs: ...`, not `docs(docs): ...`).
- **`!`** follows the type and scope when any commit on the branch carried a
  `BREAKING CHANGE:` (or `BREAKING-CHANGE:`) line. Each is moved from where
  it was written to the footer, with the lines that go on from it up to a
  blank line or the next footer, as the commit carried it. A builder or a
  reviewer writes one for a change that breaks a user's setup or a
  command's behaviour.
- **`Refs:`**: one line for each issue outside the yard the bead is linked
  to (`yardr link list`), the tracked one first, then each one it relates
  to, as stored. Never a closing word (`Fixes`, `Closes`): the hooks move a
  linked issue by the stage of the bead that tracks it ([links.md](links.md)),
  and GitHub or Linear closing it on a push would act beside them. A bead of
  another yard that this one is at, or came from, is no issue and has no
  line.
- **`Yardr-Agent:`**: one line for each distinct value on the branch's
  commits, in the order they were first seen.

A merge commit on the branch contributes its message like any other commit.
A bead that comes back after a red run keeps the squash on its branch, and the
next landing squashes again: the earlier subject line is left out and its
footers are gathered anew.
Every type of bead is squashed in this mode but a train, which lands by
rebase in either mode, so that the base gets the commit of each child; a
wagon, landing on its train's branch, is squashed like any other, and a
design bead follows the mode too. The format is fixed in the script
(`squash_message`), not configurable: a depot that wants another copies it.
`pr-merge` merges a train's pull request with `--squash` and this same subject
and body, over the pull request's commits, where its group says
`YARDR_LAND=squash` (see [Through a pull request](#through-a-pull-request)).

### Setup

```sh
install contrib/assembly/merge-local ~/.yardr/scripts/    # from main
yardr group add yardr-refinery --runner exec --limit 1 \
  --set cmd='YARDR_PUSH=origin YARDR_NOTIFY=yardmaster ~/.yardr/scripts/merge-local' \
  --set log="$HOME/.yardr/logs/refinery.log"
yardr route add --stage approved --group yardr-refinery --depot yardr --originator any
```

The route says `--originator any`: a script bills no subscription, so the
assembly lands every user's beads, not only the operator's
([groups.md](groups.md#which-beads-a-route-takes)).

The script is installed from `main` rather than run from a checkout: a bead
branch must not change how it is landed. That install is the first-time step.
Once the script is there, `yardr upgrade` refreshes it from the checkout it
builds, so a fix that lands in it is live for the next landing
([upgrade.md](upgrade.md#the-scripts)). Without a checkout of yardr, the
starter pack carries the same script: `yardr depot init <depot>`,
which is what `yardr setup` runs, installs it as
`~/.yardr/packs/starter/scripts/merge-local` and adds the group
`<depot>-assembly`, without `YARDR_PUSH` ([setup.md](setup.md)). The flow gains `merged`:

```
approved -> merged on done | new on failed | decide on question
merged terminal
```

**A PR-based variant** is the same group and route with another script. In
place of steps 4 to 7, it pushes the branch and opens (or updates) a PR, and
parks the bead until the PR is merged:

```sh
git -C "$YARDR_WORKTREE" push --force-with-lease origin "$YARDR_BRANCH"
url=$(gh pr create --head "$YARDR_BRANCH" --base "$YARDR_BASE" --fill 2>/dev/null ||
  gh pr view "$YARDR_BRANCH" --json url -q .url)
echo "PR $url" | "$YARDR_BIN" bead advance "$YARDR_BEAD" --to in-pr --note -
```

with the flow rules `approved -> in-pr | merge | new` and
`in-pr -> merged | new`, and `in-pr` routed to a manual group, or to nothing
with a subscription on the forge's merge webhook
([hook sources](subscriptions.md#hook-sources)) advancing the bead to
`merged`. Beads funneling into a shared PR push to one integration branch
instead of their own. [The public line](#the-public-line) is this variant made
real, with the pull request opened by the yard's GitHub App.

After a merge, `go install` on `main` is the whole upgrade: the running
server and daemon replace themselves with the new build within seconds, and
builders keep advancing beads through it
([configuration.md](configuration.md#upgrading)).

## 5. Merge: a merger resolves conflicts

Depot yardr does not run this stage as of 2026-10-03: its flow has no
`merge`, so a conflict goes back to `new`. The depot it was before the rename
did, and the merger's role is still in the repository
(`.yardr/roles/merger.md`); this section is how the stage works where it is
set up.

Two of the first 22 landings conflicted with what had landed since their
branch was made. Sending those back to `new` cost a full builder and Codex
cycle for what is usually a mechanical rebase, so a conflict goes to `merge`
instead.

`merge` is routed to `mergers`: a herdr group running Claude Code (Sonnet,
at most one at a time) with `prompt=roles/merger.md`. The merger reopens the
bead's worktree on `yard/<bead>` (the assembly aborted its rebase, so it is
clean) and:

1. rebases onto the depot's base;
2. resolves each conflict keeping the intent of both sides, from the bead and
   its notes on one side and the base's commits on the file
   (`git log -p <merge-base>..main -- <file>`) on the other;
3. runs the depot's test command, as its brief prints it;
4. leaves one `merge re-review:` note naming the old tip, each conflict and
   its resolution, and reports `yardr bead done`, which the flow sends to
   `review`.

The reviewer then checks only the resolution with a range-diff and advances
the bead to `approved`. The assembly picks it up again: `main` no longer
moved past the branch, so it runs the checks and fast-forwards. If `main`
moved again in the meantime and conflicts again, the bead goes back to
`merge`.

When both intents cannot be kept, or keeping them needs a real design choice,
the merger aborts the rebase, notes why, and reports `--outcome rework` (to
`new`: the builders rework the bead) or `--outcome question` (to `decide`:
Christopher chooses). It never touches `main`,
never pushes, and never forces anything but its own branch.

A red run of the tests (not a conflict) still sends the bead to `new`: the change, not
its placement on `main`, needs work.

### Setup

The yardmaster would wire this in the store; nothing in `~/.yardr` is versioned:

```sh
yardr group add mergers --runner herdr --limit 1 \
  --set kind=claude --set model=sonnet --set prompt=roles/merger.md \
  --set args='--permission-mode auto'      # as yardr-builders: it works unattended
yardr route add --stage merge --group mergers --depot yardr
```

The flow gains two rules (the rest of [`default.flow`](flows.md#worked-example-depot-yardr)
is unchanged), with outcomes so the merger reports how the merge ended
instead of naming stages:

```
approved -> merged on done | new on failed | merge on conflict | decide on question
merge -> review on done | new on rework | decide on question
```

and the assembly sends a conflicting bead to `merge`: merge-local reports
the `conflict` outcome there, having asked the flow first, and reports
`failed` back to `new` when the flow offers no `conflict` and allows no
`merge`.

## Holds

A held bead is never routed; it waits until a person or a crew member runs
`yardr bead unhold`, which routes it again from its stage (with fresh
attempts). Holding a bead ends the session working it (state `held`, not a
failure), so the daemon closes the agent's tab and the group's slot goes to
the next ready bead at once; the worktree and its branch stay. Beads get held:

- by yardr, after 3 failed sessions in one stage (an agent that died or
  exited without advancing);
- by an agent that is stuck or finds the bead unclear: it notes the question
  and runs `yardr bead hold`;
- by the reviewer, instead of a third send-back;
- by the assembly, when it cannot land without touching a dirty tree (the
  base checked out with uncommitted changes, or the bead's worktree dirty).

The yardmaster watches held beads, finds out why, and either fixes the cause and
unholds, sends it back to `backlog` to be reshaped, or sends it to `decide`.

A bead's agent can hold a bead and cannot unhold one. `yardr bead unhold`
from the pane of an agent's session is refused for every bead, its own
included, whoever held it. What an agent held waits for the yardmaster or a
person. An agent that thinks a hold can go says so in a note on the bead.
`yardr bead release` takes a bead from its group and lifts no hold.

Not every failure is the bead's. If herdr is missing or down, no bead is
held for it: the group logs one `runtime_down`, backs off (30s, doubling to
5m) and its beads wait untouched until a start works again (`runtime_up`).
A session whose agent does nothing with its first prompt (a model it may
not use, no login) raises `session_stalled` after 2m, with the end of its
pane, and its group starts no more sessions with that model; one whose
agent reports another model than asked raises `session_model_mismatch`
([groups.md](groups.md#models)). One whose harness stops on an error of its
own later (the model at capacity, a usage limit, a login that ran out)
raises `session_harness_error` on the first pass that finds it idle, with
the reason and the end of its pane (a model at capacity in answer to the
first prompt is given the prompt again first, 3 times 5 minutes apart, and
raised when that did not help)
([groups.md](groups.md#a-harness-that-stopped-on-an-error)). An agent whose
move the yard refused raises `move_refused`, with the command and why
([above](#2-new-a-builder-implements-it)). A session that
sits idle 30m or runs 4h
raises `session_idle` (with the end of its pane) or `session_aged` in the
yardmaster's inbox; with a group `grace` set it is then
stopped, and without one a session that has run twice its `max_age` is
stopped anyway and the bead released with a note; see
[configuration.md](configuration.md#session-limits-and-outages).

## Decide

`decide` is routed to the manual group `decisions`. Backlog, new, review, review-security and approved may
send a bead there with the question and the options written into the bead. Christopher
answers in `yardr review -g decisions` (or with a note and
`yardr bead advance`), and the bead goes back to `backlog` or `new`.

Decisions that are not about one piece of code are beads created straight
into `decide` and closed with the answer as the reason.

## How long the line is: the ETA

Every open bead with enough history behind it carries an ETA: a usual
range, from the medians of what its stages ahead cost to their slow
ends. `yardr bead show` prints it under the labels, and `yardr prime
--bead` with it:

```text
  eta usual 2–5h (queue ~1h behind 3 beads for muse-builders; new ~30m; review ~20m; approved after your decision)
```

The range is component-wise: each machine stage ahead — one a herdr or
exec group works — contributes its cell's claim-to-exit median to the
low end and its p90 to the high end, stretched by one plus its
send-back share, and the queue wait is added to both. It is a usual,
never a promise: sums of per-stage medians and p90s, not a calibrated
total, so every surface says "usual", never "by".

Each stage is timed for its primary group: the first group of the route
that would take the bead there. Which quota fallback takes it is chosen
when it is claimed, so the estimate names the primary group and costs
what that group's cell says. The ETA needs at least 10 claim-to-exit
durations in that group's cell to time a stage; below that it is
unclocked and named (`review: too new to time`). A stage that waits for
a person contributes no time and is named too (`approved after your
decision`). The walk follows the flow's `done` outcomes from
the bead's stage, counting at most the flow's stages and one step past,
so a loop is not walked forever; where it stops short of arrival it says
so (`then review or decide`, `then deploy on yard north`, `then review,
unrouted`, `unclocked after review`). A claimed bead's current stage
contributes what is left of its range: both ends less the run's age so
far, floored at zero. With no clocked machine stage and no clocked
queue wait, there is no ETA line or `eta` object; late is evaluated
independently and may still appear.

What the ETA leaves out it names where it can: people's stages, the
yard's cap, and wherever the walk stops. The quota's choice among a
route's groups is made at the claim and never predicted: the estimate
is for the primary group, and names it.

The queue wait is counted only for a bead no group holds, in a stage a
machine group would work; a claimed bead's queue is zero. It is a slot
simulation over the order the dispatcher claims in — priority, then
creation time. The group has as many slots as its limit, at least one;
each live session holds one until its remaining usual time, the
claim-to-exit median of its bead's label cell less the session's age;
the beads ahead of this one among those the primary group would take
are placed in order onto the earliest-free slot, each pushing it out by
its own median. The wait is when the earliest slot frees; with a free
slot and fewer beads ahead than slots it is zero, and the line omits
the queue part. Where the queue cannot be numbered it is named instead:
a bead the dispatcher cannot claim now names nothing, a yard at
`max_sessions` is `behind the yard's cap`, a paused yard is `yard paused
(max_sessions 0)`, a paused group is `group builders paused (limit 0)`,
and an unclocked bead ahead leaves it `behind 4 beads, too new to time`.
A live session whose cell
is below the floor still contributes its median remainder as a guess
when a clocked stage lets the ETA show; it cannot time the ETA by
itself.

For a page, the dispatchable order and live sessions are one shared
queue snapshot for all of its bead estimates.

The cells are kept as stages end
([groups.md](groups.md#what-a-groups-beads-cost-the-estimate-cells)); a
yard from before them replays its retained log once at upgrade, and its
open stays start their clocks then: a waiting bead counts its stage age
from the upgrade, while a running bead's clock is its live session's
start.

A bead past its stage's slow time carries a late mark:

```text
  late: waiting in new 6h, past the usual 2h (p90 entry-to-exit for difficulty:2 in muse-builders)
```

A bead no group holds is waiting-late past its whole-stay p90; one a
group holds is running-late past its claimed-run p90. Like is compared
with like: waiting time against whole stays, run time against claimed
runs. Waiting uses the primary group's entry-to-exit ring; running uses
the holding group's claim-to-exit ring. Each late clock needs 10 samples
in its matching ring. A waiting late mark can be available before the
claim-to-exit ring can time the ETA; a running mark may use a quota
fallback's cell while the ETA uses the primary group's. Thus either can
appear without the other. Held beads, people's stages, peer stages and
unrouted stages are never late. Stalled means the agent stopped — its
first prompt idle past the stall limit, told once as `session_stalled`;
late means it takes long. A bead can be either, both, or neither, and
late tells no one: there is no event for it, only the mark.

## Working a bead

The same commands for humans and agents alike:

```sh
yardr prime --bead webapp-3                  # bead, edges, notes
yardr bead note webapp-3 -                   # evidence, the words on stdin ("tests green: ...")
yardr bead advance webapp-3 --to review      # hand to the next stage
yardr bead advance webapp-3 --to new --note -  # note and move in one write
yardr bead close webapp-3 --reason "merged"
yardr bead hold webapp-3                     # stop routing; a human looks
```

Every command takes `--json`. Set `YARDR_ACTOR` so the event log shows who
acted.

A note that quotes code or file names goes in on stdin, not as a quoted
argument: inside double quotes the shell runs each backtick span and `$(`
before yardr starts, and puts what it printed in the note. `-` reads the
words from stdin, and a heredoc whose delimiter is quoted expands nothing:

```sh
yardr bead note webapp-3 - <<'NOTE'
tests green: `go test ./...`
NOTE
```

`--note -` on `done` and `advance` reads the move's note the same way. A
note with no words, empty or only white space, is refused, and so is a
`--note` given with none, whose usual cause is a shell that ran a backtick
span and had nothing to put in its place; leaving `--note` out moves the
bead with no note.

A close reason and a bead's title read stdin the same way, trailing newlines
trimmed: `yardr bead close <id> --reason -`, `yardr bead update <id> --title -`
and `yardr bead create -` (the title). Stdin is read once, so with `-b -` as
well the first line is the title and the lines after it the body, as a commit
message divides; a title alone is one line.

```sh
yardr bead create - -b - --discovered-from webapp-3 <<'BEAD'
`TestRetry` fails once in fifty runs

Seen on a loaded machine: `go test -count=50 ./retry`.
BEAD
```

A `-` with no words on stdin is refused, and nothing is closed, changed or
created. An explicit `--reason ""` still closes the bead with no reason.

### Dependencies

Work that spans several beads and must land as one unit is a
[train](#trains). Work that can land bead by bead is a chain instead:
`yardr dep add <blocker> <bead>` orders it.

A dependency's kind is a free word. Only `blocks` (the default) keeps a bead
from being ready, and only `parent` makes a child of a train; any other kind
is a record. One has a meaning of its own: `discovered-from`, from a bead to
a bead that was found while working on it. `yardr bead create "<title>"
--discovered-from <bead>` makes the bead and the edge in one write (the
origin may be open or closed, in any depot; an unknown one creates nothing),
and the new bead inherits nothing from it. `yardr bead show` says
"discovered from" on the one and "led to" on the other,
`yardr bead list --discovered-from <bead>` lists what was found from a bead
(`-a` for the closed too), and `yardr dep rm <origin> <found> -k
discovered-from` removes it. It never affects `yardr ready`, routing, a
train's children or what lands.

One word is not free: `yardr dep add` refuses the kind `folded`. A fold makes
that edge, from the bead it makes to each bead it folds, and it records what
the fold took from that bead: the stage it stood in, the issues it tracked,
the beads it blocked and who watched it (`yardr dep list --json` shows it as
`moved`). An edge made by hand would say a bead was folded that never was.
`yardr dep rm` refuses it too: only folding and unfolding change which beads
belong to a carrier. `yardr bead show` says "folded into" on the one and
"folded from" on the other ([Folding beads](#folding-beads)).

A bead's agent can add edges and cannot take a `blocks` edge away. From an
agent's session pane `yardr dep add` works, and the security stage uses it to
make a bead wait for the weakness it filed. `yardr dep rm` is refused for any
`blocks` edge, plain or staged, between any two beads. It is refused for
`-k parent` on a train's child too, because that also removes the child's
`blocks` edge. Edges of any other kind are removed as before. An agent that
filed a wrong edge says so in a note on the bead, and the yardmaster or a
person removes it. Otherwise a builder could remove the edge a reviewer filed
and land its bead with the weakness still open.

A `blocks` edge can hold only where it matters: with `--at <stage>` the
bead waits only while it is in that stage, and with `--until <stage>` its
blocker releases while it is in that stage or past it along `done`. The
yard says the condition wherever the edge is read. `dep list` prints the
stages it names (`yardr-x7wf -blocks-> footplate-xq35 at approved`, `...
until review`), `bead show` says `blocked by yardr-x7wf at approved` for
the edges holding it, and prime's `BLOCKED BY` carries the same
conditions. `yardr ready` lists only beads that are ready, so the beads
the gate holds are read with `yardr ready --waiting`: one line per
holding edge, with why (`footplate-xq35  waits at approved until
yardr-x7wf closes`, `footplate-xq35  waits until yardr-x7wf is in
review`). A ready bead held only by its group is listed too, with the
route that matched it and the group's count and limit
(`footplate-xq35  new  waits for builders (2 of 2) by route k2abc
(label difficulty:1)`).

Both flags are for kind `blocks` only. `--at` names a stage of the
target's own flow and `--until` a stage of the blocker's, and a stage
its flow has not got is refused; where no flow governs the bead any
well-formed stage name is accepted. Two edges may join the same beads
when their stages differ: the useful pair is `dep add yardr-x7wf
footplate-xq35 --until review`, which lets the target start once the
contract is visible as code, plus `dep add yardr-x7wf footplate-xq35
--at approved`, which still lands it only after the blocker closes. A
single edge may name both: held at one stage until the blocker reaches
another. `dep rm` takes the same two flags and removes exactly that
edge. Closing always releases, so won't-do releases like merging; a
blocker that goes back holds again at the target's next hand-over, and
a running session is never stopped.

Stage an edge only on a written contract: use `--until` only when the
contract the target builds against is written down (docs/api.md or the
like) and the target's gate passes without the blocker on the base,
name the blocker's commit in the target's body, and watch the blocker
with the edge (`yardr bead watch <blocker> --crew yardmaster --kind
advanced`), so every move it makes reaches you until it closes.

The store logs the gate's flips on the target: `unblocked` when a write
opens it, `reblocked` when one closes it again, with `blockers` naming
the sorted blockers whose holding changed. Both are plain bead kinds,
heard through a kind subscription (`yardr subscribe yardmaster yardr
--where kind=unblocked --where kind=reblocked`); a blocker move that
leaves the gate unchanged logs none, which is what the watch above is
for. A watch ends when the blocker closes; if a later reopen closes
the target's gate again, the target's `reblocked` event reports it.
And `bead close` prints what
the close releases: `releases <ids>` names the open targets whose gate
this close opens, so the yardmaster sees the consequence before
deciding.

### Bead history

```sh
yardr bead history webapp-3                  # when, who, what; a diff under each change of the body
```

A bead holds what it is now. What it was is in the event log and nowhere
else: an `updated` event carries the previous value of every field it
changed (`was`), the body among them. `yardr bead history <id>` prints the
bead's events, the oldest first, and the bead's page of the web view shows
the same.

The history lives as long as the events do. `yardr store prune`, which the
daemon runs every hour, removes events older than `YARDR_EVENT_RETENTION`
(90 days), of open beads as of closed ones, and the old titles and bodies
on them go too: there is no second copy and no "last N versions". Set the
retention to `off` to keep every version for good
([configuration.md](configuration.md#retention-keeping-yarddb-bounded)).

### Bead ids

Every bead has two names. Its **handle** (`webapp-k3f9`: the depot, or
`--prefix`, then random base32) is what yardr prints and what branches
(`yard/<handle>`), worktrees and herdr labels are built from; it is chosen
once and never changes. Its **UUID** (a UUIDv7) is its identity: the store
is keyed by it, so ids need no central counter. `--json` shows both
(`id` is the handle, `uuid` the UUID); `--id` on create picks the handle.

Commands accept the UUID, the handle, or a unique prefix of the handle
with at least 4 characters after the `-` (`webapp-k3f`... is too short; an
ambiguous prefix lists its candidates).

A UUIDv7 starts with its creation time, so the store's key order is
creation order, and listings use it. Handles are random and carry no
order: never sort by handle.

## Trains

A train is work that spans several beads and must land on main as one
unit. It is a bead of type `train`; its children are the beads with a
`parent` edge from it:

```sh
yardr bead create "Trains" -t train -d yardr
yardr dep add <train> <child> -k parent
```

- **Branch(b)** is `yard/<id>` for every bead; the train's branch is
  Branch(train).
- **BaseOf(b)** is Branch(parent train) for a child of a train, and the depot's
  base for everything else, the train itself included. `yardr bead show`
  prints it as `base` (and `train`, and a train's `children`; the same
  fields are in `--json`).

A child goes through the same flow, groups and tests as any bead; only its
base differs. When a child is first started and the train's branch does not
exist yet, the herdr runner creates it from the depot's base tip (fetched
first when the base is a remote's) and logs `train_branched` on the train
with the commit. An existing train branch is never recreated or moved. The
child's worktree is branched from the train's branch, and `YARDR_BASE` in
the agent's and the assembly's environment is BaseOf(b), so merge-local
rebases the child onto the train's branch, lands it there and pushes that
branch; main does not move. A test script the depot names by its path is
then read from the train's branch, which is what the child lands on. The
bar for main is still main's: integrate-train tests the train as a whole
with the copy the depot's base has, before main moves.

`dep add -k parent` refuses a parent that is not a train, a closed train
(it has landed, or was dropped: a child added now would land on a branch
nothing integrates again), a child already in another train, a train as a
child (trains do not nest) and a child in another depot. Only parent edges
from a train count: a bead whose parent is not a train keeps the depot's
base. A bead that is a child of two trains
anyway (a type changed to `train` later) is not dispatched; yardr logs
`bad_train` until one parent edge is removed.

`yardr bead list`, `yardr ready` and `yardr session list` show each
bead's train in a TRAIN column after the bead (empty for a bead with no
train), and their `--json` rows carry it as `train`. `yardr bead list --train
<train>` lists only that train, first, and its children. In herdr, a child's
workspace is labelled `<group> [<train>] <bead>` (e.g. `builders [sv6b]
2cet` for `yardr-2cet`) and any other bead's `<group> <bead>` (`builders
cbdc`): the workspace sits under the depot's node, so the depot prefix is
trimmed from the ids and the group, and the group goes by its `label`
config when set ([groups.md](groups.md#herdr-setup)). The workspace is
reused across stages and relabelled with the current group on each; each
stage's tab mirrors it with the stage in front, `<stage> [<train>] <bead>`
(`review [sv6b] 2cet`).

`dep add <train> <child> -k parent` also adds `<child> -blocks-> <train>`, so
one command makes the child and keeps the train from being ready until the
child closes; `dep rm <train> <child> -k parent` removes both edges.

### A chain or a train

Work of several beads is a chain unless it has to be a train (an epic, in
most trackers). In a chain `yardr dep add <blocker> <bead>` gives the order
([Dependencies](#dependencies)), and each bead lands on the base by itself,
where it can be installed and tried. Make a train (`yardr bead create - -t
train -d <depot>` with the title on stdin, then `yardr dep add <train>
<child> -k parent` for each child) when half of the work must not be on the
base, because it would break or confuse what is there until the rest lands;
or when several children are built in parallel in one area and need one
review of the whole before anything reaches the base.

A train costs this: its children land on the train's branch, `yard/<train>`,
so nothing reaches the base, or can be tried from it, until the whole train
is reviewed and merged. A directory depot has no branches: a train there only
groups its children for one review of the whole
([dir-depots.md](dir-depots.md)).

Before a depot's first train, read `yardr flow show <depot>`: a train may
follow a flow of its own ([the train's own flow](#the-trains-own-flow)), and a
train in a stage no route serves waits for a person.

When the work for an issue outside the yard is a train, the train tracks it:
`--tracks <issue>` on `bead create`, or `yardr link move <issue> --to <train>`
from the bead that started it. In a chain the last bead tracks it, so its
mapped stages follow the chain's progress; the others take `--relates
<issue>`. [links.md](links.md) has what a link does and the rules for one.

### Wagons

A wagon is a child of a train that takes a shorter road to the train's
branch. It is for several pieces of one feature, built in parallel, that
are not worth having on main one by one: each piece would otherwise pay
for the whole suite at its landing and a review of its own, and the
assembly lands one bead at a time. A wagon pays for a plain run of the
tests, twice, and no review; the whole suite and the reviews (the second for
security alone) happen once, on the whole train, before main moves. Everything about the train itself is as above
and below: nothing changes in what a train needs to reach main.

```sh
yardr bead create "Trains" -t train -d yardr
yardr bead create "The parser" -t wagon -d yardr
yardr dep add <train> <wagon> -k parent
```

A depot has this lane when it has a flow for type `wagon`
(`yardr flow show <depot>` lists it). A train sent on to review names each
wagon in its body or in a note, because the train's review must cover each:
it is the only review they get.

- **The type.** A wagon is a bead of type `wagon`. In depot yardr the type has
  a flow of its own, [`.yardr/flows/type/wagon.flow`](../.yardr/flows/type/wagon.flow):
  the depot's flow without `review` (`new -> approved on done`). The depot's
  routes for `new`, `approved` and `decide` carry no type, so wagons go to the
  same builders and the same assembly as any bead.
- **How a wagon is tested.** With the depot's test command, without
  `YARDR_LANDING`. What a command makes of that is the depot's own. Depot
  yardr formats, vets and builds everything, then tests the packages the
  branch changed, their importers, and the packages its reads table names.
  It runs without `-race`, whatever the wagon changed: the race detector runs
  at landing only, on the whole train. The builder runs it
  before `done`, as the builder of any bead does; merge-local runs it again
  on exactly what lands, where any other bead gets the run with
  `YARDR_LANDING=1`.
- **What a wagon's run is compared with.** Its train's branch, not the
  depot's base: "what the branch changed" is what this wagon changed, not the
  train's earlier wagons again. `YARDR_BASE` is `yard/<train>` for the
  builder's session and for merge-local, which has just rebased the wagon
  onto it, and depot yardr's script compares with `YARDR_BASE`. The first
  line says so, and that the run is not raced (`test: what changed since
  yard/<train> (YARDR_BASE), from <sha>: testing without -race (race runs at
  landing only, docs/testing.md R4)`). The train's own run tests everything,
  with the race detector, before main moves.
- **When merge-local leaves `YARDR_LANDING` out.** The exec runner tells a
  script the bead's type and its train (`YARDR_TYPE`, `YARDR_TRAIN`, the
  latter empty for a bead with no train). merge-local runs the test command
  without `YARDR_LANDING` only when all three hold: the type is `wagon`,
  there is a train, and the base it lands on is that train's branch.
  Everything else is a landing, as before: a task that is a child of a
  train, and a wagon with no train, which would land on the depot's base. A
  wagon's landing note says `merged <sha> (+<n> code, +<m> test) on yard/<train>,
  tested with <what ran> without YARDR_LANDING in <n> s; the landing run and
  the review are train <train>'s`.
- **A wagon needs a train.** The quick run and the missing review are only
  safe where the whole suite and a review still stand before main, so yardr
  keeps a wagon with no parent train in the stage its flow starts in
  (`backlog`): `bead advance`, `bead done` and `bead create -s <stage>`
  refuse to put it anywhere else, saying how to give it a train
  (`dep add <train> <wagon> -k parent`) or make it a task
  (`bead update <wagon> --type task`). A wagon that lost its train after it
  moved (`dep rm -k parent`), or that no flow governs, is not started by any
  agent or script: the dispatcher logs `wagon_without_train` once, and only a
  manual group still gets it. It can be taken back to `backlog`.
- **The train pays.** integrate-train rebases the train's branch, lowers its
  file size table (a wagon's landing on the train's branch leaves the rows to
  it), and runs the test command on it with `YARDR_LANDING=1` as for any
  train, and a red run adds a fix child. The train's reviewer is told that
  wagons were not reviewed, nor tested as a landing is, one by
  one ([`.yardr/flows/yardr.train/review.md`](../.yardr/flows/yardr.train/review.md)),
  and reviews each; the security review reads each again. So keep a train to
  about five wagons, which one review can hold, and leave single fixes on the
  normal path.

### The train's own flow

A train follows `yardr.train` ([flows.md](flows.md#worked-example-depot-yardr)).
As of 2026-10-03 depot yardr has the flow but not the groups for it: `open`,
`merge`, `in-pr` and `land` have no route, so a train there waits for a
human until the [setup below](#setup-2) is done. The steps describe the
path with that setup:

1. **backlog**: the yardmaster shapes the train and adds its children, then
   advances it to `open`.
2. **open**: the train waits while any child is open (they block it). When
   the last child closes it is ready, and the route for type `train` in
   `open` sends it to `yardr-integrators`, an exec group running
   [`contrib/assembly/integrate-train`](../contrib/assembly/integrate-train).
   The integrator fetches the base when it is a remote's, rebases
   `yard/<train>` onto the depot's base in the train's worktree, lowers the
   file size table of a test command that carries one to the train's files
   (merge-local's step 2, once for the train: a commit of its own on the
   branch, `assembly: lower filesizes rows to actual`, since the head is a
   child's landed commit; held on the same grounds, and past the same
   `YARDR_REWRITE_TIMEOUT`, 120 seconds unless set), runs the
   depot's test command on it with `YARDR_LANDING=1` (a script named by its
   path is the copy main has) and `YARDR_TEST_BEADS` (the train's children:
   the command's `YARDR_BEAD` is the train),
   pushes the rebased branch when `YARDR_PUSH` is set (replacing the remote
   branch only when everything on it was in what it rebased, or in a
   recorded old tip; step 5), and reports `done`, to review. A red run
   reports `failed`, back to `open`, after adding a child in `backlog` to
   fix it ("Fix the tests on train <id>", type bug). The note and the child's
   body carry what merge-local's note does: the branch, the commit, the base
   and what ran, then the last 200 lines of the output. The child
   blocks the train, so it is not integrated again until the fix has landed
   on its branch. A rebase that conflicts aborts it and reports
   `conflict`, to `merge`, with the conflicting files and both tips in the
   note (step 5). A test command that says it could not run (exit 2) or a
   branch it cannot work on (missing, dirty, nothing ahead of the base)
   holds the train with a note. A depot with no test command sends the
   train to review untested, and the note says so. A run ended by a signal
   (exit 128+N) is run once more, as
   merge-local does, and holds the train if a signal ends it again; no
   child is added for it.

   A train reported `failed` back to `open` with no child to wait for (the
   push or the pull request failed: GitHub down) is not integrated again on
   the daemon's next pass. Each return to the stage it was in, in a row,
   doubles the wait before the next try, from the daemon's backoff (30s) up
   to an hour, so an outage is retried less and less often rather than on
   every pass; the daemon logs each wait once on the train as a `backoff`
   event, with the count. The count is read from the train's events, so a
   restarted daemon keeps waiting; it starts over when the train enters the
   stage any other way or a human un-holds it.
3. **review** and **review-security**: `yardr-reviewers` reviews the whole
   diff, `<base>..yard/<train>`: the train's brief says it is a train, names
   its children and gives the range. Changes go back to `open` (`--outcome
   changes`) after adding the fix as a child; without one the train would be
   integrated again unchanged. `done` sends the train to `review-security`,
   where another agent reads the same diff once more for security alone
   ([`.yardr/flows/yardr.train/review-security.md`](../.yardr/flows/yardr.train/review-security.md)),
   every wagon among it and what the wagons open together; its `done` goes to
   `approved`, its `changes` back to `open` as the first review's. A train has
   no `done-safe`: it is always read twice.
4. **approved**: the train lands, through a pull request (below) or
   locally: `yardr-refinery` and merge-local land `yard/<train>` on the depot's
   base exactly as a bead's branch (BaseOf(train) is the depot's base) and
   advance it to `merged` by the flow's bare `approved -> merged` edge. A
   red run there reports the flow's `failed` outcome, which for a train is
   `open` (merge-local falls back to `new` only for flows without it).
5. **merge**: a conflict between the train's branch and the depot's base,
   from the integrator in `open` or from merge-local or pr-train in
   `approved`, goes to the mergers as any bead's does. The merger rebases
   `yard/<train>` onto the base in the train's worktree, keeping both sides'
   intent, runs the tests, and does not push (the integrator pushes, with a
   lease); the brief says the branch and what happens next. The tip the
   merger starts from is recorded on the train as `old tip: <sha>`, by the
   integrator's conflict note and again by the merger's note (as for any
   bead): the remote still has that tip, which the rebase rewrote, and the
   integrator's lease accepts a remote branch whose commits are all in the
   branch as it was before its own rebase or in a recorded old tip, so the
   resolved branch replaces it. A remote with commits in neither is never
   forced over: the train is held, or mailed about when there is no pull
   request. Its `done` sends the train back to `open`, not to review: with
   no child open it is ready, so the integrator takes it again, rebases it
   (a no-op unless the base moved again), tests it, pushes it and opens or
   updates its pull request, and the train goes to review as what will
   land. `rework` also goes to `open` (add the fix as a child first),
   `question` to `decide`.

### Through a pull request

**Experimental, and off by default.** A train lands locally (step 4 above)
unless `YARDR_PR=1` is in the cmd of every group on this path: the
integrators, `yardr-pr` and `yardr-pr-merge`. Without it integrate-train opens
no pull request, and pr-train and pr-merge hold the train with a note naming
the switch, before pushing, merging or asking GitHub anything, so a stray
route or a move by hand does not start the path: nothing reports `done` in
`approved`, and the train reaches `merged` only by merge-local's bare edge.

Do not switch it on for a repository others can open pull requests
against while it is experimental. Its known limits:

- **Green is the base branch's required checks.** The daemon lands a
  train when every check the base requires (branch protection or a
  ruleset) is green on the reviewed commit
  ([GitHub events](#github-events)). A base that requires none is never
  green to it: a human says merge.
- **A commit status sends no event.** A required check an external CI
  reports as a commit status is read with the rest, but only
  `workflow_run` and `check_suite` deliveries have the state read again;
  a train waiting on a status alone waits for a human, or for the next
  event about its pull request.

With `YARDR_PR=1` set, a train goes to main as a pull
request against the depot's base instead of a local fast-forward. Three exec
groups (limit 1 each) and two type routes do it, besides the integrators.

A train is bound to one pull request, not to its branch's name, which a
fork's pull request can carry too. integrate-train stores the binding in the
train's metadata when it opens the PR: `pr_url`, `pr_number` and
`pr_head_repo` (owner/name of the repository the head branch is in). No
script looks a PR up by branch: pr-train and pr-merge read the bound one
and compare what GitHub says of it (number, head repository, head branch)
with the binding; a difference holds the train, untouched. A train bound to
none reports `failed`, to `open`, where integrating binds it.

What is merged is the reviewed commit and no other. As the train enters
`in-pr`, pr-train stores the commit it pushed, the branch as the reviewer
approved it with their own commits, in the train's metadata as
`pr_reviewed_sha`, beside the binding. pr-merge merges with
`--match-head-commit <pr_reviewed_sha>`: a PR whose head is any other
commit, pushed after the review, is not merged, and the train is held in
`land` with a note naming both shas. CI is read for that commit too
([GitHub events](#github-events)).

- **open**, `yardr-integrators`: after pushing the rebased branch (it needs
  `YARDR_PUSH`; set without it, the train is held), integrate-train opens a
  PR for `yard/<train>`, titled `<train title> (<id>)`, its body the train's
  body, a "Children" list (ids and titles) and the trailer `Train: <id>`; if
  the train is bound to an open PR already it replaces that PR's body, and a
  bound PR that was closed or merged gives way to a new one. The URL goes
  into the note, and the binding (`pr_url`, `pr_number`, `pr_head_repo`)
  into the train's metadata. A PR open for the branch that the train is not
  bound to (opened by hand, say) is not adopted: the train is held until
  someone binds it (`yardr bead update <train> --meta pr_url=<url>`; the
  next integration stores the rest) or closes that PR. A push or `gh` that
  fails reports `failed`, back to `open`, so the next integration retries,
  each time after a longer wait (step 2 above); a remote branch with
  commits the train lacks is held.
- **approved**, `yardr-pr`
  ([`contrib/assembly/pr-train`](../contrib/assembly/pr-train), with
  `YARDR_PR=1`; held without it): pushes
  `yard/<train>`, which may carry the reviewer's commits (with a lease: a
  remote branch with commits of its own is never overwritten), replaces the
  PR's body with the first review's note under "Review" and the security
  review's under "Security review" where it has one, stores the pushed
  commit as `pr_reviewed_sha`, and reports `done`,
  to `in-pr`. No bound PR, a refused push, or a PR GitHub reports as
  conflicting with the base reports `failed`, to `open`, for the integrator.
- **in-pr**, `decisions` (members mckean, yardmaster): a manual stage. Look at
  the PR and its checks; `yardr bead done <train>` means "merge it" (to
  `land`), `--outcome changes` sends it back to `open` (add the fix as a
  child first), `--outcome question` to `decide`. The daemon does this
  itself when the required checks of the reviewed commit are green
  (below).
- **land**, `yardr-pr-merge`
  ([`contrib/assembly/pr-merge`](../contrib/assembly/pr-merge), with
  `YARDR_PR=1`; held without it): runs `gh
  pr merge <pr_url> --rebase --delete-branch --match-head-commit
  <pr_reviewed_sha>` (with `YARDR_LAND=squash` in the group's cmd, `--squash`
  with the subject and body of [Landing by squash](#landing-by-squash)
  written for the train over the PR's commits, and the train is one commit on
  the base), then `git fetch` and `git
  merge --ff-only <remote>/<base>` in the depot's checkout, and reports
  `done`, to `merged`, which closes the train. A PR whose head is not the
  reviewed commit, when pr-merge looks or when GitHub refuses the merge for
  it, holds the train, unmerged: bring the new commits into the train's
  branch and send it back to `open` to have them reviewed, or put the
  remote branch back at the reviewed commit and unhold. A train with no
  `pr_reviewed_sha` reports `failed`, to `open`. A merge GitHub refuses
  for another reason
  (checks pending, review required, conflicts) reports `failed`, to `open`,
  with gh's message, once. The checkout must be on the base and clean, or
  the train is held before anything is merged.

### GitHub events

With a github hook ([subscriptions.md](subscriptions.md#github)) on the
repository, the daemon moves a train on what GitHub reports about its pull
request, so a PR that is green and approved waits on no one. What an event
means is not in the daemon: the hook carries a table of what its events say
([links.md](links.md#the-sources-events-move-the-bead)), and each line
names an outcome, which is reported for the train as a session reports one
(`yardr bead done --outcome`). This flow's edges route it. The daemon reads
every `hook` event whose `train` field (the head branch is `yard/<train>`)
names an open train, in seq order, and puts those that are about the pull
request the train is bound to (below) to the table of the hook that
recorded them. A held train is a human's: it is left where it is (the event
is judged, and logged as ignored because the train is held) until it is
un-held, after which the next event moves it; its CI is not read while it
is held, and is read when it is un-held.

The table this flow is written for, set on the yard's hook with `yardr hook
add` (it replaces the hook's definition, so the lines go with the rest of it;
`yardr hook show gh` prints them):

```sh
yardr hook add gh --source github --secret-file ~/.yardr/github.secret \
  --as yardmaster \
  --says "event=pull_request action=closed merged=true type=train -> merged: PR merged" \
  --says "event=pull_request action=closed merged=false type=train -> question: PR closed unmerged: reopen, or drop the train?" \
  --says "event=pull_request_review action=submitted state=changes_requested sender=user association=owner association=member association=collaborator type=train -> changes: Changes requested on the PR" \
  --says "event=workflow_run event=check_suite action=completed conclusion=failure conclusion=timed_out stage=review stage=review-security type=train -> changes: CI failed on the head of the PR" \
  --says "event=ci conclusion=success stage=in-pr type=train -> done" \
  --says "event=ci conclusion=failure stage=in-pr type=train -> changes"
```

These are the lines the starter pack sets on the hook, each for trains alone
(`type=train`): the hook's table is shared with the packs that carry the same
source, whose lines are for the beads of other types, and an import of the
starter pack sets only these among them ([packs.md](packs.md#how-a-pack-maps-to-the-yard)).
A yard whose hook serves trains alone may leave `type=train` out.

The hook acts as a crew member because the table's `event=ci` lines are
read with that member's credential, as a move is; a hook with an
`event=ci` line and no `--as` is refused, as is one whose source declares
no `ci` command (the `github` pack's setup notes walk it).

1. **PR merged** is `merged`, which `approved`, `in-pr` and `land` route to
   `merged`: one move, also for a pull request merged by hand, whose
   checkout catches up at the next fetch. A train in `land` whose
   yardr-pr-merge session is still running is moved as any bead is by a
   `done` from outside its session: the session ends with the move, and its
   own `done` afterwards is refused as stale.
2. **PR closed unmerged** is `question`: a train in `review`,
   `review-security` or `in-pr` goes to `decide` with "PR closed unmerged:
   reopen, or drop the train?".
3. **Changes requested** by one of the repository's own people
   (`sender=user`: a login ending in `[bot]` is a bot; the yard posts no
   reviews, as pr-train writes its review into the PR's body; and
   `association=owner association=member association=collaborator`, what
   GitHub says the reviewer is to the repository, so a review from anyone
   else moves nothing) is `changes`: from `review`, `review-security`,
   `approved` and `in-pr` the train goes back to `open` with the review in the
   note, where its integrators take it up again. A table that does not ask
   who wrote the review still moves the train, and its note leaves out the
   words of anyone outside those three and points at the review by its URL.
   Comments (`issue_comment`) have no line: a crew member subscribed to
   github with `--scope mentions` gets them.
4. **CI red, in `review` or `review-security`**: a `workflow_run` or
   `check_suite` completed with conclusion `failure` or `timed_out` on the
   head is `changes` too, and the line holds in those two only
   (`stage=review stage=review-security`). A `cancelled` run or suite is not
   red: someone, or a newer push, stopped it, so it says nothing about the
   commit.
5. **CI, in `in-pr`** (`event=ci`): not taken from an event. CI is state,
   read from the source through its `ci` command, and an event only has it
   read again (see "CI is read as state" below). What was read is put to
   the table as an event of its own, green as `done` (to `land`) and red
   as `changes` (to `open`).

A stage with no edge for the outcome refuses it: a pull request merged
while its train is in `open` moves nothing, and the train's events say why
(`refused`, with the outcome and the stage). A depot whose train flow names
its stages otherwise gives its hook its own lines, and a hook without a
table moves nothing: each event about a train is then logged as ignored,
with that reason.

For a run or suite, the head commit is the one the last `pull_request` event
(opened, synchronize, ...) or review for the train carried, kept in the
train's metadata as `pr_head`; without one the daemon reads it live
through the source's `pr` command. A failure on another commit (a run a
later push superseded) is ignored. The command is asked about the bound
pull request, by its URL or number, never by the branch.

**CI is read as state.** For a train in a stage the table has an `event=ci`
line for (`in-pr` here; a line that names no stage has every open train's
CI read) the daemon takes no conclusion from an event. It runs the
source's `ci` command about the reviewed commit, `pr_reviewed_sha`: the
pull request's head and base, the checks the base branch requires (its
protection's required status checks and those of the rulesets that apply
to it), and the check runs and commit statuses on that commit, the latest
of each name. Then:

- **green**, every required check is there and concluded `success`
  (`neutral` and `skipped` count as success): the event
  `event=ci conclusion=success`, so the train goes to `land` with the note
  "CI green on <sha>: <checks> (the checks <base> requires)", and
  yardr-pr-merge merges it, in the same pass;
- **red**, a required check concluded `failure`, `timed_out` or
  `startup_failure`, also while others still run: the event `event=ci
  conclusion=failure`, so the train goes to `open` with the failed checks
  and the first one's URL in the note;
- **pending**, a required check is queued or running, was `cancelled`,
  waits for someone's approval, or has not been reported at all: nothing
  moves. One green workflow among several required ones is pending.

It asks when it first sees the train in `in-pr`, so CI that finished while
the train was under review, or while the daemon was down, is seen without
any new run; after that, a `workflow_run` or `check_suite` delivery of any
action or conclusion, a `pull_request` event or a review about the bound
pull request has it ask again, as does any change to the train (a note, an
un-hold). Between those nothing is polled. A read GitHub does not answer
is tried again after 30s, doubling up to an hour.

Checks that are not required are not counted, failed or not. A base that
requires no checks has nothing the daemon can call green (a workflow that
has not reported yet cannot be told from one that does not exist), so the
train stays for a human; a failed check on the commit still sends it back
to `open`. A pull request whose head is no longer the reviewed commit is
left alone: pr-merge would not merge that head. A train with no
`pr_reviewed_sha`, or bound to no pull request, is not asked about. A
required check is matched by its name, whichever app reports it.

The branch name only finds the train; the bound pull request (`pr_url`,
`pr_number`, `pr_head_repo`, which integrate-train stores) decides whether
the event counts. An event is ignored, logged as such, and sets no
`pr_head` when it is in another repository than the PR's, names another
pull request number, or has its head in another repository than
`pr_head_repo`: a fork's pull request from a branch of the same name has
its own number and head repository, and a workflow run on a fork's branch,
for which GitHub lists no pull request, still names the fork as its head
repository. A merged event for a number the train is not bound to therefore
does nothing. A train bound to no pull request is moved by no event, and
one bound before the number and head repository were stored (`pr_url`
alone) is held to the URL's repository and number, its head taken to be in
that repository.

A delivery reaches the table once. The hook listener drops, before any
event is logged, a delivery whose body the hook has recorded (by its
sha256) or whose `X-GitHub-Delivery` id it has: the id is a header the
signature does not cover, so a captured delivery sent again under a new id
is caught by its body, which is signed. Both keys are written in the
transaction that records the delivery
([subscriptions.md](subscriptions.md#redeliveries)).

Each event
judged for a train is recorded in its metadata (`hook_seq`), so a daemon
that restarts and reads the log again from the start does nothing twice.
Every move (`action`), every move the flow or the stage's group refused
(`refused`), and every event left alone because of the train's hold, its
pull request or a hook without a table (`ignored`) is logged as a
`hook_rule` dispatch event on the train, with the hook, the event's type
(`event`), the line it matched (`says`) and its `outcome`, the train (as
`bead` and `train`; a bead of another type that tracks the event's thread
is moved the same way and has `bead` alone,
[links.md](links.md#the-sources-events-move-the-bead)), its
`stage`, the sha and the hook event's seq. Every read of a train's CI is
logged the same way, as event `ci` with no seq: what it did (`green: in-pr
-> land`), or why it did nothing (`pending: waiting for <checks>`).

The daemon acts as `yard`, so the group holding `in-pr` must list it among
its members (below); otherwise its moves out of `in-pr` are refused, and the
`hook_rule` event says so. A repository should make every workflow that
must pass a required check of the base branch: those are what the daemon
waits for, and what GitHub refuses the merge without (pr-merge then
reports `failed`, to `open`, and the next integration tries again).

`gh` (logged in as the operator) and `jq` must be on the scripts' PATH.
Without `YARDR_PR`, the default, route `approved` for trains to
`yardr-refinery` (or leave the stage route alone) and nothing else changes:
merge-local lands the train locally and advances it to `merged`, the bare
edge kept for it.

### Setup

```sh
install contrib/assembly/integrate-train ~/.yardr/scripts/   # from main
yardr depot flow yardr --type train yardr.train                  # the repo's .yardr/flows/yardr.train.flow
yardr group add yardr-integrators --runner exec --limit 1 \
  --set cmd='YARDR_PUSH=origin ~/.yardr/scripts/integrate-train' \
  --set log="$HOME/.yardr/logs/integrator.log"
yardr route add --stage open --type train --depot yardr --group yardr-integrators --originator any
```

Each install is the first-time step. Once a script is there, `yardr upgrade`
refreshes it from the checkout it builds, `pr-train` and `pr-merge` below
included, so a fix that lands in one is live for the next run
([upgrade.md](upgrade.md#the-scripts)).

Through pull requests (experimental, see above), every cmd on the path
carries `YARDR_PR=1`:

```sh
install contrib/assembly/pr-train contrib/assembly/pr-merge ~/.yardr/scripts/   # from main
yardr group add yardr-integrators --runner exec --limit 1 \
  --set cmd='YARDR_PUSH=origin YARDR_PR=1 ~/.yardr/scripts/integrate-train' \
  --set log="$HOME/.yardr/logs/integrator.log"
yardr group add yardr-pr --runner exec --limit 1 \
  --set cmd='YARDR_PUSH=origin YARDR_PR=1 ~/.yardr/scripts/pr-train' \
  --set log="$HOME/.yardr/logs/pr.log"
yardr group add yardr-pr-merge --runner exec --limit 1 \
  --set cmd='YARDR_PUSH=origin YARDR_PR=1 ~/.yardr/scripts/pr-merge' \
  --set log="$HOME/.yardr/logs/pr-merge.log"
yardr route add --stage approved --type train --depot yardr --group yardr-pr --originator any
yardr group add decisions --runner manual --limit 50 --members mckean,yardmaster,yard   # yard: the daemon, for the hook rules
yardr route add --stage in-pr --type train --depot yardr --group decisions --originator any
yardr route add --stage land --type train --depot yardr --group yardr-pr-merge --originator any
```

The train flow's stage file for review (`.yardr/flows/yardr.train/review.md`,
shown in the reviewer's brief) says how a train is reviewed as a whole, and
how it is reviewed on its pull request: the
reviewer pushes its fix-forward commits to `yard/<train>` with a lease (the
one branch any role pushes; the merger does not push even that one, the
integrator pushes its rebase), and posts its review on the PR. GitHub
refuses `--approve` and `--request-changes` from the login that opened the
PR, which is the operator's, the same login the reviewer's `gh` uses: on
its own PR the reviewer posts a `--comment` with the verdict in the note's
first line, and the yard learns the verdict from `yardr bead done`.

## Folding beads

Small changes to one depot are built and reviewed better as one bead than
as one bead each: one builder session, one review, one landing. `yardr bead
fold` makes that bead by hand, as the shaper and the yardmaster did by
retitling one bead and closing the others:

```sh
$ yardr bead fold yardr-ab12 yardr-cd34 yardr-ef56
yardr-k9p2 folded from yardr-ab12, yardr-cd34, yardr-ef56 (3 points, size:medium difficulty:1), in ready
```

The new bead is the **carrier** and each bead it was made of a **member**.
The line names the members in the order given, then what they weigh, the
`size:` and `difficulty:` the carrier got, and the stage it starts in;
`--json` prints the carrier with `members` and `points`. The fold is one
write, all or nothing:

- The carrier's body holds each member's body as a part, in the order given
  (`## Part 1: <title> (<id>)`), and ends in a `## The bundle` section: it is
  done when every part's done-when holds and the depot's test command is
  green, each part its own commit starting with the part's bead id. Its title
  is `<depot> bundle: <title>; <title>`, cut on a word at 100 characters with
  `(+n more)`; `--title` replaces it.
- It takes the highest priority of the members, the oldest member's
  originator, their type when they share one (else the oldest's) and their
  flow. It carries their labels but `size:` and `difficulty:`, which it gets
  of its own: `difficulty:` the highest of theirs, `size:` from what they
  weigh, a small bead 1 point, a medium one 2, a large one 4 and one with no
  size 2. One point is small, two to four medium, five or more large.
- Each member is closed "folded into <carrier>", behind a `folded` edge from
  the carrier ([Dependencies](#dependencies)), and its open stage asks are
  taken back. What it tracked moves to the carrier, the beads it blocked are
  blocked by the carrier with the stages the edges named, and whoever
  watched it watches the carrier. A bead tracks one issue per source, so a
  second issue of a source the carrier tracks is linked to it instead. A
  member's notes and files stay on it: a note on the carrier says how many
  notes each holds and which files, to be read with `yardr bead show
  <member>`, and names the issues no bead tracks now.
- A `folded` event on the carrier names the members, the points, the stage it
  starts in and `hand`.

The members must be open, not worked by a session, of one depot and one
flow, and this yard's own: a bead that came from another yard and has not
gone back, or is away at one, is refused. A bead a manual group holds is not
worked by a session, since its claim is a person's turn and nothing runs. It
is folded, and the fold ends the claim. A bead that an open bead blocks
(`yardr bead show` says `blocked by`) is refused, naming the blocker: the
fold re-points what a member blocks and not what blocks it, so the carrier
would be ready while the blocker is open. Fold it once the blocker closes,
leave it out, or take the edge off with `yardr dep rm` when the order no
longer matters. A blocker folded with it does not refuse, since it closes in
the same fold. An edge that holds a bead only at another stage (`--at`)
refuses too, naming the blocker and the stage, since the carrier would pass
that stage with the blocker still open; only an edge its blocker has released
(`--until`) holds nothing and is not refused. A bead that is a child of
a train (`yardr bead show` says `train`) is refused too, naming the train: the
carrier is a new bead outside it, so it would branch from and land on the
depot's base and not the train's branch. It could not build on what the
train's other children landed there, and its work would reach main alone,
ahead of the train's own run and reviews. Take the bead off the train with
`yardr dep rm <train> <bead> -k parent` (which takes its blocks edge to the
train too), fold, and put the carrier on the train with `yardr dep add <train>
<carrier> -k parent`. Only a parent edge from a bead of type `train` makes a
child, and a closed train does not change it: the bead's base is its branch
still. A bead's agent cannot fold, since its pane may not make the call; a
person or a crew member can. A fold of one bead is refused, since its carrier
would be that bead with a worse title.

The carrier starts in `--to`. Without it, it starts where its members wait:
in the stage they all wait in, or, when that stage is a siding (a stage worked
by a manual group that sets `fold`, `fold_after` or `fold_max`, see
[groups.md](groups.md#a-siding)), in the first stage its flow leads to
from the siding, since a siding is where beads wait to be folded and not
where the fold waits. Members in different stages have no stage to start
in, and the command asks for `--to <stage>`.

`yardr bead show` says where a bead stands in a fold, under the lines for
where it was found from: `folded into <carrier> <title>` on a member, and
`folded from <member> <title>` on a carrier, a line for each, with `(closed)`
after a bead that is. `--json` has both as `folded_into` and `folded_from`,
lists of `{id, title, status}` that are there and empty when there is
nothing to list. A bead is folded into more than one carrier only if it was
reopened and folded again, and show names each.

A reviewer who finds one part wrong and the rest good takes that part out
instead of sending the whole carrier back:

```sh
$ yardr bead unfold yardr-k9p2 yardr-cd34 --reason "part 2 breaks the gate on linux"
yardr-cd34 reopened in backlog, out of yardr-k9p2; revert its commit on yard/yardr-k9p2
```

The part reopens in `--to`, or in the flow's first stage without it, with the
reason as a note, and what the fold moved from it comes back: the issues it
tracked, the beads it blocked with the stages the edges named, and whoever
watched it. A target two parts moved stays on the carrier until the last of
them is out, so each part restores exactly what it moved. The folded edge is
gone, the carrier's body gains the taken-out line under `## The bundle`, and
an `unfolded` event is logged on it. Each part is its own commit starting with
the part's bead id, so the reviewer reverts that commit on the carrier's
branch and goes on reviewing. A bead that is not a member of the carrier is
refused.

## Posting a pull request's review

The reviewer of a pull request from outside reads a stranger's text, and it
holds no key on purpose: whatever talks it into something would have what the
yard's GitHub App has. So its review is data, and a script posts it, as the
public line's reviews are posted ([below](#the-public-line)). A `pr` bead of
the contributors pack ([packs.md](packs.md#the-contributors-pack)) that the
reviewer found ready, or that needs changes, goes to `review-post`, and
[`contrib/assembly/post-review`](../contrib/assembly/post-review), the `cmd` of
an `exec` group of the yard's own, posts the review the reviewer stored, as the
App, and sends the bead on: `done` to `ciwait`, `changes` to `contributor`. The
reviewer stores it in the update that records the head it read, and reports the
same outcome:

```sh
yardr bead update <id> --meta reviewed_head="$(git rev-parse HEAD)" --meta review='{
  "outcome": "done",
  "body": "What the change does, and the findings, each with its file and line…",
  "comments": []}'
```

It is one script with two modes: a bead of type `pr` takes the rules below, and
every other bead keeps the public line's. What the two share is kept as it is:
the pull request's URL must be `https://github.com/<owner>/<repo>/pull/<n>`, the
pull request must be open, the review is anchored to the head the reviewer read
(`reviewed_head`) and refused when GitHub says the pull request has another head
now, the review's fields are checked one by one and the request is made from
them by `jq`, and the App's token goes to `gh` in its environment and to no
argument, note or log. What a pull request from outside changes:

- **The pull request is the one the hook linked.** The public line binds the
  review to the bead's own branch, which a contributor's pull request is not:
  it comes from a fork, or from a branch of theirs. The bead has no `own_pr`
  either. What says which pull request the bead is of is its tracks link, and
  the script posts only if the hook that made the bead made that link
  (`created_by` is `hook:<name>`). A link a person or an agent of the yard made,
  which an agent cannot do to a `pr` bead past triage anyway
  ([links.md](links.md#the-rules)), is held, not posted on.
- **Always a comment, never an approval or a request for changes.** Merging is
  a maintainer's, and a request for changes would stand on the pull request
  after its author had acted, since nothing posts again: the bead's routing
  carries the consequence, and the review is a comment whatever it says. The
  first line is still the verdict, written by the script (`Approved`, `Changes
  needed`), and the stored review is emptied once it is posted, so that it is
  posted once.
- **No label.** The script gives the bead no `merge-ok` and takes none off. The
  reviewer's grant for a bot's bump of Go modules and a maintainer's yes are as
  they were ("Merging pull requests", below).
- **Findings are in the body.** The reviewer stores `comments` as `[]` and puts
  each finding in `body` with its file and line; the script still checks inline
  comments as it does for the public line, and posts one if it is given.
- **A review it cannot post goes back to the reviewer, never with an order to
  push.** The pull request is its author's, and the reviewer pushes nothing. A
  review none stored, one with a field wrong, a `done-safe` (which the contributors
  flow has no way for), no recorded head, a pull request that has moved since
  the head was read, or a comment GitHub refuses, is failed back to `review` with
  the reason in a note, which tells the reviewer to read the pull request as it
  is now, record that head and store the review again. The flow allows one such
  return, then sends the bead to `decide`; the flow counts the rounds back to
  `review`, whichever outcome made them, so a bead that a push already brought
  back to be read goes to `decide` the first time. What is not the reviewer's to
  put right holds the bead in `review-post` with a note, for the operator to put
  right and `yardr bead unhold <id>`: a link the hook did not make, a pull request
  that is not open, no App inputs, a mint that fails, any other answer from GitHub.

A question for a person is never posted: it goes to `decide`. A push to the pull
request while the script runs is the source's word, by the pack's lines, as it
is under review: new commits on a pull request a maintainer accepted take the
bead back to `triage` (`unaccepted`), and a bot's send it back to `review`
(`pushed`), so that a head nobody accepted is not read before a person has said
yes to it, and the run is stopped with the move. A person's push to a pull
request no maintainer accepted is no event of this stage: the script's check of
the head sends a review of a head the pull request no longer has back to
`review`. A merge or a close of the pull request ends the bead from
`review-post`, as from every stage a bead waits in, and the run is stopped.

### Setup

The group is the yard's, made once, for the public line's posting stages and
this one: one group, `yardr-post`, serves both. Its `env_file` is the App's id
and the path of its key file, the same file the groups of the sections below
have, and the github source's `mint_command` is the mint, as there. The App needs
Pull requests read and write on the repository, to read the head and post a
review.

```sh
install contrib/assembly/post-review ~/.yardr/scripts/                 # from main
yardr group add yardr-post --runner exec --limit 1 \
  --set cmd="$HOME/.yardr/scripts/post-review" \
  --set env_file="$HOME/.yardr/env/pr-merges.env" \
  --set log="$HOME/.yardr/logs/yardr-post.log"
yardr pack apply contributors --depot <depot> --group post=yardr-post …   # the pack's flow, and its route for review-post
```

`--group post=yardr-post` maps the pack's group to the yard's for every depot
(the flag is repeatable, so the same apply maps `--group pr-ci=pr-ci` too, as
the next section has it), and the apply writes the route for each:
`review-post`, type `pr`, to `yardr-post`. A yard whose `pr` flow is its own
routes the stage by hand instead (`yardr route add --stage review-post --type pr
--originator any --group yardr-post`). The script is refreshed by `yardr
upgrade` from the checkout it builds, once installed
([upgrade.md](upgrade.md#the-scripts)); the pack carries a copy that a test
holds equal. The reviewer's role is what stores the review,
and the pack's flow is what sends the bead to `review-post`, so a yard that
upgrades the script applies the pack again too: a yard that has not keeps its
old flow and role, and its reviewer's `done` goes straight to `ciwait` with
nothing stored or posted.

## The yard as the CI of a pull request

The yard is the CI of a pull request, whether or not the repository has GitHub
Actions. A `pr` bead of the contributors pack
([packs.md](packs.md#the-contributors-pack)) that the reviewer found ready
waits in `ciwait`, and [`contrib/assembly/pr-ci`](../contrib/assembly/pr-ci),
the `cmd` of an `exec` group of its own (`pr-ci`, limit 1, so one run at a
time) that the pack's flow gives the stage to, runs the depot's own test
command on the exact head the reviewer read, on the yard's machine, and says
how it went. It is the only CI of a repository with Actions off, and where
Actions runs it is still the check merge-pr relies on (`ci_head`, below):
GitHub's own check runs are not asked. It reads the pull request from the
bead's tracks link and asks GitHub as the yard's App, as merge-pr does
(below), and:

- refuses a bead that is not in `ciwait`, before it fetches anything: the
  stage is the one after a reviewer has read the pull request, and the yard
  runs a pull request's code nowhere before that, a fork's least of all;
- reads the pull request's head from GitHub and holds the bead, for a pull
  request that waited in `triage`, unless that is the commit a maintainer
  accepted there, before it fetches anything. The yard records the commit as
  the bead's `accepted_head` when the label `accepted`, put on by a person,
  moves the bead out of `triage`: the head the event named. A maintainer who
  moved the bead by hand records the one they looked at, `yardr bead update
  <id> --meta accepted_head=<sha>`, and a bead with none recorded, or one
  that is no full sha, is held the same way. The note names both commits and
  the command, and once a maintainer has read the head and recorded it as the
  one they accept, `yardr bead unhold <id>` runs the tests again. A bead's
  agent may not write `accepted_head`, on its own bead or another's; a bead
  that never waited in `triage` (a trusted author's or a bot's pull request,
  made in `review`) has none and is held to the next check alone;
- reads the pull request's head from GitHub and holds the bead unless that is
  the commit the bead's reviewer read, before it fetches anything. The
  reviewer records the commit as the bead's `reviewed_head` right before it
  reports `done`: the head its worktree stands on, which the yard fetched when
  its session began (where its sandbox lets it fetch it looks at the head once
  more first, and the read-only sandbox reaches no network). A pull request
  pushed to since, whose event came late or never, has another head: the bead
  is held, the note names both commits, and `yardr bead advance <id> --to
  review` (then `yardr bead unhold <id>`) has the pull request read as it now
  is. A bead with no `reviewed_head` is held the same way. A bead's agent
  writes `reviewed_head` on its own bead only (the rule for `merge-ok`,
  whatever actor the command names), and a person on any, a maintainer who has
  read the head themselves included;
- fetches `refs/pull/<n>/head` from the depot's `origin` with the operator's
  own git credentials, and checks that exact commit out, detached, in a
  worktree of its own beside the bead's (`<worktrees>/<depot>/<bead>-ci`),
  which it removes when it ends, however it ends;
- runs the depot's test command there, the one every landing runs
  (`yardr depot show`). Where the command is a file the base has
  (`.yardr/test`), the **base's** copy of it runs, never the pull request's,
  so that a pull request cannot change the script that judges it; any other
  command runs as the pull request's own files make it. It runs with
  `YARDR_LANDING=1` and without the App's id and key file, because this is
  the pull request's landing run: merge-pr merges a head this run passed on
  and no landing by the assembly follows, so no other run of the command
  stands between the head and the base. Depot yardr's `.yardr/test` then runs
  what a bead's landing does, the selection plus the six black-box suites
  under `-race`, and the whole suite for a change it cannot select (a
  dependency bump's `go.mod` or `go.sum`). The exit codes mean what they do
  in merge-local: 1 and the like are red, 2 is "could not run", above 128 is
  a signal and is run once more, and a run past `YARDR_TEST_TIMEOUT` (1800
  seconds besides what it waited for the race lock) is killed and is red;
- on green, asks GitHub for the head once more. The same commit is recorded
  on the bead as `ci_head` and reported `done`, to `approved`, with a note
  naming the commit and which test ran; another commit means the pull
  request was pushed to meanwhile and is reported `changes`;
- on red reports `changes`, to `contributor`, with the end of the output
  (200 lines) in the note.

A push to the pull request while the bead waits or the tests run moves the
bead before any report, by the pack's lines for the source: a person's push is
`changes`, to `contributor`, and a bot's is `pushed`, back to `review` to be
read at the new head. On a pull request that waited in `triage`, every push
is `unaccepted` instead, whoever pushed and whether or not the label
`accepted` is still on it: the bead goes back to `triage` from `review`,
`review-post`, `ciwait` and `contributor`, and nothing of the new head is read
or run until a person has said yes to it. After looking at the new head, a
maintainer adds the label `accepted` again; if it is still there, take it off
and put it on again. A label put by a bot does not say yes. The run is stopped
with its session, and a report of it that still comes is refused.
The script's own reads of the head, against `accepted_head` and
`reviewed_head` when it starts and against the commit it tested at the end of
the run, are for a push whose event has not come yet or never will.

A merge or a close of the pull request ends the bead the same way, in this
stage as in `triage`, `review` and `contributor`: the pack's lines say
`merged` or `dropped`, the bead goes to `merged` or `closed`, the run is
stopped and a report of it is refused. A run that finds the pull request
over before the source has said so holds the bead (next paragraph), and no
event moves a held bead: `yardr bead advance <id> --to merged`, or `--to
closed`.

Whatever is no verdict on the pull request holds the bead in `ciwait` with a
note and reports nothing: no token, GitHub or the fetch refusing, a depot with
no test command (a pull request is not called green untested), tests that
could not run or that a signal ended twice, a pull request that is no longer
open, a head that is not the one its reviewer read. The operator puts it
right, then `yardr bead unhold <id>` runs the tests again. Nothing is written
to GitHub, no commit status and no check run: the
App has no permission for the first, and nothing would read either. What
reads the verdict is merge-pr, which merges only a head that is the bead's
`ci_head`. So `ci_head` is the script's and a person's to write, and a bead's
agent is refused it, on its own bead as on another (`yardr bead update --meta
ci_head=…` from its pane): the reviewer reads a stranger's text, and a pull
request that talked it into saying the tests passed would be merged untested.

The pull request is the one the bead's tracks link names, when the script runs
and again when merge-pr does, so once a `pr` bead has left `triage` the link
is not a bead agent's to change. `yardr link add` of a tracks link and `yardr
link rm` of one are refused to an agent, on any such bead and on the one it
works ([links.md](links.md#the-rules)). Without that, a remove and an add
would do what `yardr link move` does, which is a person's, and the check of
`reviewed_head` would not stop the reviewer of the bead, who can record the
head of the new pull request too. A maintainer re-points the link by hand,
from their own terminal.

The tests of a pull request run on the yard's machine, as whoever runs the
yard, in no sandbox: a fork's code runs as the operator, after a reviewer has
read it, and for a pull request from outside only at the commit a maintainer
accepted. That is the accepted cost of a CI that is free, and a wall around the
run is a design of its own (yardr-design-w87q).

### Setup

```sh
install contrib/assembly/pr-ci ~/.yardr/scripts/                 # from main
yardr group add pr-ci --runner exec --limit 1 \
  --set cmd="$HOME/.yardr/scripts/pr-ci" \
  --set env_file="$HOME/.yardr/env/pr-merges.env" \
  --set log="$HOME/.yardr/logs/pr-ci.log"
yardr pack apply contributors --depot <depot> --group pr-ci=pr-ci …   # the pack's flow, and its route for ciwait
```

The `env_file` is the App's id and the path of its key file, the two lines
merge-pr's group has ("Merging pull requests", below): the same file serves
both, and the github source's `mint_command` is the mint, as there. The App
needs Pull requests read on the repositories, for the head. The group is the
yard's, made once, and `--group pr-ci=pr-ci` maps the pack's group to it for
every depot, so their runs queue one behind another, and a run of depot yardr
waits for the test gate's race lock as a landing does, since it is raced (the
wait does not count against `YARDR_TEST_TIMEOUT`). A pull request to depot
yardr that changes `go.mod` or `go.sum` runs the whole suite, so a machine
that needs more than the default 1800 seconds for that sets a longer
`YARDR_TEST_TIMEOUT` in the group's `cmd`. The apply writes the route for each
depot:
`ciwait`, type `pr`, to `pr-ci`. A yard whose `pr` flow is its own routes the
stage by hand instead (`yardr route add --stage ciwait --type pr --originator
any --group pr-ci`), a default that a later apply with the mapping leaves to
work the stage. The script is refreshed by `yardr upgrade` from the checkout
it builds, once installed ([upgrade.md](upgrade.md#the-scripts)); the pack
carries a copy that a test holds equal. The script tests only a head the
reviewer recorded as `reviewed_head`, and the pack's reviewer role is what
records it, so a yard that upgrades the script applies the pack again too. A
pull request that waits in `ciwait` before then is held until its head has been
read and recorded (`yardr bead advance <id> --to review`, then `yardr bead
unhold <id>`). Likewise a pull request that waited in `triage` is tested only
at its `accepted_head`, which the daemon records from the label once it is
upgraded; applying the pack again brings the flow's `unaccepted` edges. The
upgraded daemon sends a changed head back to `triage` even if the label was
removed. One accepted before then has no `accepted_head`, and is held until a
maintainer records the commit they accept, `yardr bead update <id> --meta
accepted_head=<sha>`, and unholds it.

## Merging pull requests

A pull request from outside is a `pr` bead of the contributors pack
([packs.md](packs.md#the-contributors-pack)). Reviewed, and green on the
yard's CI (the section above), it waits in `approved`, and from there either a
maintainer merges it on GitHub or the yard does. The yard does for the beads
that carry the label `merge-ok`, with [`contrib/assembly/merge-pr`](../contrib/assembly/merge-pr),
the `cmd` of an `exec` group of its own (`pr-merges`, limit 1, so one merge
at a time) that a yard-default route sends them to. The label is the whole
of the permission: the reviewer gives it to a bot's bump of Go modules and
to nothing else, and a maintainer's yes for any other pull request is one
command that gives it with the head commit they looked at:

```sh
yardr bead update <id> --add-label merge-ok --meta merge_head=<sha>
```

A bead's agent gives `merge-ok` on its own bead only, which is all the
reviewer does for a bump, and is refused `merge_head` on any bead, its own
included: the sha is recorded by a person.

merge-pr reads the pull request from the bead's tracks link, which must be
`https://github.com/<owner>/<repo>/pull/<n>` and nothing else, and asks
GitHub as the yard's App with an installation token minted for that one
repository (the github source's `mint_command`, from the App's id and key
file in the group's `env_file`: no secret of its own, and the operator's `gh`
login is never used). What it merges is the commit of the yes:

- a bot's pull request from a branch of the repository's own is merged at the
  head it has now: such a bot rebases all the time, and a recorded sha would
  hold every one of its pull requests;
- everything else (a fork, a person's branch, a bot's fork) is merged at the
  bead's `merge_head`, a full sha, and at no other. A head that is another
  commit holds the bead with "moved since your yes", and a bead with no
  `merge_head` holds with the command that says yes.

Either way the yard's CI must have passed on that commit, which is the
bead's `ci_head` (the section above), and `--match-head-commit` has GitHub
refuse the merge if the head moves while it is made. A branch of the repository's own is
rebased on and deleted; a fork is merged with a merge commit and its branch
is left alone, being its author's.

A pull request already merged reports `merged`, and one closed unmerged
`dropped`; those are the only outcomes merge-pr reports. Everything else
that stops it (no label, no yes, a head that moved, no CI of the yard on the
head, the App without the permissions it needs, any refusal of GitHub) holds
the bead with a note saying why, and nothing was merged: a maintainer acts on
GitHub, then unholds the bead and it is looked at again. Nothing retries. A
pull request pushed to since its tests ran, a bot's included, has no CI on
its new head and is held with "CI has not passed on <head>": `yardr bead
advance <id> --to ciwait` has the yard run the tests again (the bead is held,
so `yardr bead unhold <id>` too), and the bead comes back to `approved` with
the new head recorded. The tests run on a head a reviewer read: for one none
did, `ciwait` holds the bead (above) and `yardr bead advance <id> --to review`
has the pull request read first.

### Setup

```sh
install contrib/assembly/merge-pr ~/.yardr/scripts/              # from main
install contrib/github-mint/github-mint ~/bin/                   # once, if the github source has no mint
yardr source set github mint_command=$HOME/bin/github-mint
# The App's id and the path of its key file, which are no secret, for the owner alone:
( umask 077; printf 'GITHUB_APP_ID=%s\nGITHUB_APP_PRIVATE_KEY_FILE=%s\n' <id> <key file> > ~/.yardr/env/pr-merges.env )
yardr group add pr-merges --runner exec --limit 1 \
  --set cmd="$HOME/.yardr/scripts/merge-pr" \
  --set env_file="$HOME/.yardr/env/pr-merges.env" \
  --set log="$HOME/.yardr/logs/pr-merges.log"
yardr route add --stage approved --type pr --label merge-ok --originator any \
  --group pr-merges --note "the yard merges a pr bead marked merge-ok; the label outranks a depot's approved/pr to decisions"
```

A group whose cmd sets `YARDR_LAND=squash` merges a branch of the repository's
own as one commit on the base, with the pull request's title and body as its
message, instead of rebasing it (a fork is merged with a merge commit either
way); any other value holds the bead before anything is merged.

The App needs Contents and Workflows read and write on the repositories (the
second is what lets it merge a pull request that changes a workflow file),
beside the Pull requests and Checks permissions the yard's other calls of
GitHub use. Each depot with `pr` beads routes the others
to a person, so the label alone moves a bead to merge-pr and nothing else
does: `yardr route add --stage approved --type pr --depot <depot> --originator
any --group decisions`, which its type ranks before the depot's plain
route. Without that route a depot's own
assembly (the route for `approved`, no type) would run merge-local on a
pull request's bead. The script is refreshed by `yardr upgrade` from the
checkout it builds, once installed ([upgrade.md](upgrade.md#the-scripts)).

## The public line

Depot yardr has a second line, on which its own work goes through a pull
request on GitHub, in public: the bead's branch is pushed and opened as a pull
request by the yard's GitHub App, the reviewers read it and store their review
on the bead, a script of the yard posts each review on the pull request as the
same App, the yard runs the depot's tests on the head they read, and the App
merges it. It is the flow
[`yardr.public`](../.yardr/flows/yardr.public.flow), with its stage files in
[`.yardr/flows/yardr.public/`](../.yardr/flows/yardr.public): the default flow
with four stages added, `pr` after `new`, `review-post` after `review`,
`review-security-post` after `review-security` and `ciwait` before `approved`,
and every stage name the default flow has. The old line is untouched, and a bead
that is not pinned to the new one follows it as before.

```
                   done-safe ────────────────────────────────────────────────┐
                                                                             ▼
new ──▶ pr ──▶ review ──▶ review-post ──▶ review-security ──▶ review-security-post ──▶ ciwait ──▶ approved ──▶ merged on main
 ▲      │                      │                                      │                   │
 └──────┴────── changes ───────┴──────────────────────────────────────┴───────────────────┘
```

| stage | worked by | what happens |
|---|---|---|
| `new` | the builders | as on the old line; every commit message is public |
| `pr` | [`open-pr`](../contrib/assembly/open-pr) | pushes `yard/<bead>`, opens its pull request or updates the one it has, as the App; the bead tracks it |
| `review`, `review-security` | the reviewers | read the branch as before, push the commits they make, store their review on the bead with the head they read (`review`, `reviewed_head`), and report `done`, `done-safe` or `changes` as before; they post nothing |
| `review-post`, `review-security-post` | [`post-review`](../contrib/assembly/post-review) | posts the stored review on the pull request as the App, gives `merge-ok` with the approval that sends the bead to the tests, and sends the bead on the way the review says |
| `ciwait` | [`pr-ci`](../contrib/assembly/pr-ci) | runs the depot's test command on that head ([above](#the-yard-as-the-ci-of-a-pull-request)) |
| `approved` | [`merge-pr`](../contrib/assembly/merge-pr) | merges it as the App ([above](#merging-pull-requests)), squashed where the group says `YARDR_LAND=squash` |

Changes go back to `new` from `pr` (nothing to publish, or a conflict with the
base), `review-post`, `review-security-post` and `ciwait`, three rounds together
as on the old line, and the builder's next report of `done` pushes to the pull
request it has. `open-pr` records it as the bead's own (`own_pr`), so that the
bead's sessions stay on its branch instead of standing on the pull request's
head as if it were somebody else's change ([links.md](links.md#two-kinds)). A
question for a person goes to `decide` from `review` and `review-security` as
on the old line, and is not posted.

### The reviewers hold no key

Posting a review takes a token of the App, which is minted from its private key,
and a reviewer is the agent least fit to hold that key: it reads other people's
text (a diff, a bead's body, on another line an outsider's pull request) and
runs shell commands in its pane, so whatever talks it into something has what
the App has, to open, merge and push on the repository past every review and
test. The key stays where it was, in the environment of the exec groups of fixed
scripts (`open-pr`, `post-review`, `pr-ci`, `merge-pr`) and in no agent's. The
reviewers' part is data. A reviewer stores its review on its bead, in the update
that records the head it read, and reports its outcome:

```sh
yardr bead update <id> --meta reviewed_head="$(git rev-parse HEAD)" --meta review='{
  "outcome": "done-safe",
  "body": "What the change does…",
  "comments": [{"path": "internal/x/y.go", "line": 42, "body": "…"}]}'
```

`outcome` is the one it reports (`done`, `done-safe` or `changes`), and the
GitHub review is made from it: an approval for the first two, a request for
changes for the third, with the verdict (`Approved`, `Changes needed`) written
as the first line of the body by the script. `post-review`, which the two
posting stages run, reads that and the bead's stage, tracks link, `own_pr` and
`reviewed_head`, and nothing else of the bead (not its body, not its notes), and
posts only what it checks:

- the pull request is the one the bead tracks, which must be its `own_pr`, open,
  and from the branch `yard/<bead>` of the repository it is addressed in:
  `own_pr` is metadata an agent can write, so it is the pull request that says
  whose branch it is, and a bead pointed at another pull request is held;
- the review is of the head GitHub says the pull request has (`reviewed_head`);
  a pull request that moved since is sent back to the reviewer to be read as it
  is;
- the review's fields are valid, one by one (an outcome the stage takes, a body
  of 1 to 60000 bytes, at most 50 comments, each with a path inside the
  repository, a line from 1 and text), and the request is made from them by `jq`,
  never interpolated into a shell line;
- the token goes to `gh` in its environment and to no argument, note or log.

When it is posted the script gives the bead `merge-ok` if the review sends it to
the tests (`done-safe` at `review-post`, `done` at `review-security-post`),
empties the stored review so that it is posted once, and reports the review's
outcome. If the yard refuses `done-safe` because the diff touches
`.yardr/security_paths`, the script removes `merge-ok` and holds the bead for a
person to send it to `review-security`; the review is already on the pull request,
so it must not be posted again. A review it cannot post as stored (none stored, a
field wrong, the pull
request moved, a comment GitHub refuses because its line is not in the diff)
goes back to its reviewer once, with the reason in a note, and the second time
to `decide`: the flow counts the arrivals at the review stage, whichever outcome
made them, so a bead that went round through `new` has used its one retry
already and goes to `decide` the first time. What is not the reviewer's to put
right (a pull request that is not the bead's own or is closed, no App inputs, a
mint that fails, any other answer from GitHub) holds the bead in the posting
stage, for the yard to put right and unhold.

What a misled reviewer can still do is write a review that says the wrong thing
about its own bead, which it always could: the script does not read the text for
what it means. The rule on what may be said is in the reviewers' stage files and
is theirs alone to keep.

### What is posted

- **The pull request.** Its title is the squash subject line the landing writes
  ([Landing by squash](#landing-by-squash)): the type, the scope, the bead's
  title and its id. Its body is made from the branch's commit messages, then
  `Yardr-Bead` and `Yardr-Agent` as the squash commit has them. Nothing of the
  bead's body or notes is read into either, and both are written again each
  time the branch is pushed.
- **The reviews.** One GitHub review for each reviewer, as the App, with inline
  comments on lines of the diff, anchored to the head the reviewer read. GitHub
  does not let the account that opened a pull request approve it or ask changes
  of it, and the App opens these, so the review goes up as a comment review and
  its first line is the verdict. The posted text describes the change and the
  code only: it quotes no bead body or note, and names no customer, lead, price
  or other context that only the yard has. That rule is in the reviewers' stage
  files for the line, and the full review is still a note on the bead.
- **The yes.** `merge-ok` is given by `post-review`, with the approving review
  that sends the bead to the tests, and `open-pr` takes it off whenever it
  pushes a new head. No reviewer says it.
- **The merge.** With `YARDR_LAND=squash`, one commit on the base whose message
  is the pull request's title and body.

Comments that outsiders make on these pull requests arrive as hook
deliveries, for a person to read, as for any pull request.

### Going onto it, and back

A bead goes onto the line when it is pinned, by whoever routes the work (a
bead's own agent may not pin its flow), in any stage before `pr`:

```sh
yardr bead update <id> --meta flow=yardr.public
```

and goes back by moving it out of `pr`, `review-post`, `review-security-post` and
`ciwait` if it is in one (`yardr bead advance <id> --to new`, or `--to review`
or `--to review-security`), taking the yes off (`--remove-label merge-ok`) and
taking the pin off (`--meta flow=`). It then lands by merge-local as before; a
pull request left open is closed on GitHub by hand, and a review stored and not
posted stays on the bead, unread. Pointing the depot itself at the flow
(`yardr depot flow`) is a later step with a consequence of its own: a store
pointer takes the repository's type flows out too
([flows.md](flows.md#which-flow-governs-a-bead)).

### Setup

The groups and routes are the yard's, not the repository's. `pr-ci` and
`pr-merges` are the groups of the two sections above, and the line adds one for
`open-pr`, one for `post-review`, and one for the merge that squashes. Those
exec groups are the only ones that get the App's id and key file, in the
`env_file` they share with the other two; no group of reviewers, builders or
shapers has them.

```sh
install contrib/assembly/open-pr contrib/assembly/post-review ~/.yardr/scripts/   # from main
yardr group add yardr-pr --runner exec --limit 1 \
  --set cmd="YARDR_PUSH=origin $HOME/.yardr/scripts/open-pr" \
  --set env_file="$HOME/.yardr/env/pr-merges.env" \
  --set log="$HOME/.yardr/logs/yardr-pr.log"
yardr group add yardr-post --runner exec --limit 1 \
  --set cmd="$HOME/.yardr/scripts/post-review" \
  --set env_file="$HOME/.yardr/env/pr-merges.env" \
  --set log="$HOME/.yardr/logs/yardr-post.log"
yardr group add yardr-pr-merges --runner exec --limit 1 \
  --set cmd="YARDR_LAND=squash $HOME/.yardr/scripts/merge-pr" \
  --set env_file="$HOME/.yardr/env/pr-merges.env" \
  --set log="$HOME/.yardr/logs/yardr-pr-merges.log"
yardr route add --stage pr --depot yardr --originator any --group yardr-pr
yardr route add --stage review-post --depot yardr --originator any --group yardr-post
yardr route add --stage review-security-post --depot yardr --originator any --group yardr-post
yardr route add --stage ciwait --depot yardr --originator any --group pr-ci
for type in task bug feature; do
  yardr route add --stage approved --depot yardr --type "$type" \
    --label merge-ok --originator any --group yardr-pr-merges
done
```

The `approved` routes ask for a label by name, so they rank before the depot's
route to the assembly, which the beads of the old line (they never carry
`merge-ok`) still take. They are limited to task, bug and feature beads so
pull-request beads from the contributors pack keep their existing route. These
routes put the trial on depot `yardr` only. The App needs Pull requests read
and write on the repository, for opening a pull request and posting a review,
beside what the two sections above name. A group with no App in its environment
holds the bead in its stage with a note, and the bead waits until the
yardmaster restores it.

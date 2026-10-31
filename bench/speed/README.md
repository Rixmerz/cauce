# Speed benchmarks: where cauce's wall time goes, and what shortens it without costing quality

Real workers, real money. Each benchmark measures one thing cauce could do faster, beside what it
does today, and keeps the result that decides it.

```bash
python bench/speed/overlap.py <commit> 3            # cauce's check beside the verifier, or after it
python bench/speed/build.py run sonnet/high,sonnet/xhigh,opus/high,opus/xhigh 3 4 && python bench/speed/build.py report
python bench/speed/plan.py run opus/high,opus/xhigh,opus/max 2 3 && python bench/speed/plan.py report
python bench/speed/handoff.py run self,cauce 4 4 && python bench/speed/handoff.py report
python bench/speed/dispatch.py current,named2 3 && python bench/speed/dispatch.py report
python bench/speed/build.py run sonnet/high,sonnet/high+batch 4 4      # a `+batch` arm asks for parallel calls
python bench/speed/versus.py run cauce,opus/low,opus/medium 3 3 [--hard] && python bench/speed/versus.py report
```

## Summary: what was measured, built, left alone, and never measured

Every row below is a real run judged by hidden tests or by cauce's own records; each links to its
section. Three to four runs a cell is noisy: a difference under about 20% is not read as one.

**Built, because a measurement showed it:**

| Change | Release | Evidence |
|---|---|---|
| cauce's check runs beside the independent verifier | 0.45 | A: −42% on the median, the check not slowed |
| features start at sonnet/high (was sonnet/xhigh) | 0.45 | B: as right, 3 to 4 times sooner |
| a plan starts at opus/high (was opus/xhigh) | 0.45 | C: the same parts in half the time |
| the worker does not run the full check before it reports | 0.47 | E: 131 s against 216 s, as right |
| the dispatcher's wait names a collision | 0.47 | F: independent pairs started 42/42 (was 29/42), colliding ones held |
| a start rises only on climbs | 0.48 | G: history had pinned writing kinds a rung or two high |
| the mod hears an ending within about 2 s | 0.48 | H: 9 s p50 and 16 s p90 before |
| notes are filed after the ending | 0.49 | J: 5.3 s p50 off every step |
| a writing kind classified high starts at its ladder's first cell | 0.50 | M: 213 s against 468 s, as right |
| the session passes the kind it read (`--kind`) | 0.50 | L, O: skips a 6 s classifier call |
| the verifier runs after the ending (`late_verifier`), `cauce run` exits with it | 0.51 | R: the harder build in 122 s against 203 to 213 s |
| Opus at low effort is no cheap cell | 0.51 | Q: two of three medium builds climbed for nothing |
| a plan classified high is not raised to opus/xhigh | 0.51 | C, and plans in real use: 47% first-try at opus/xhigh, p50 10 min |

**Measured and not built, and why:**

| Idea | Why not |
|---|---|
| the verifier at sonnet/medium or opus/low | K, Q: 20 and 18 of 42 bugs where high catches 27 |
| the verifier at opus/medium | Q: 36 of 42, but 81 s and three times the cost; a candidate, not proven on more changes |
| a turn cap on the verifier | Q: no faster, no fewer bugs missed |
| asking workers for parallel tool calls (`+batch`) | I: slower on both builds |
| starting held work before its predecessor's verifier ends | D: nothing in the templates waits on a verified step |
| starting a review before the build's check ends | D: one review in four thrown away, to save about 65 s of a 15 to 40 minute build |
| Opus for the classifier or the dispatcher | O: one more right in 72, at 20 to 37 times the cost, no faster |
| splitting a build whose halves read each other | P: slower, and the merged tests failed |
| a guidelines CLAUDE.md (`andrej-karpathy-skills`) in cauce's workers | N: diffs 4 to 15% smaller, no arm but opus/low faster |
| skipping cauce's check after the worker ran it | the overlap hides it wherever a verifier runs; about 4% elsewhere |
| splitting a review with no parts by folder | `bench/review/areas.py`: slower and dearer |

**Do not change without a new measurement:**
- *The verifier's cell (the work's model at high effort).* Every cheaper cell measured missed a
  third of the bugs; it found blockers in 16 of 53 checks here.
- *Writing kinds' starts.* Raising them for complexity or for passes where they started made
  builds 2 to 5 times slower and no more right (B, G, M).
- *The rule that a dispatcher's wait names a collision.* Its old caution held every
  independent pair back (F).
- *Haiku as the delegator.* Measured against Opus and Sonnet (O).
- *Racing a start that rarely passes its first try.* It judges itself in each repository
  (`cauce.racing`); a fixed answer here would undo that.

**Never measured:**
- throughput of several tasks at once across separate repositories, and the capacity level's
  rises and halvings under a real rate limit;
- the late verifier's false alarms and the reopenings it causes in real use, and how often a
  session merges a branch before its late check has spoken;
- the verifier at sonnet/xhigh, or opus/medium on more than one change;
- a build in a real product repository with a browser check (every build here is a small Python
  engine with `make test`);
- builds on a cell other than sonnet/high and opus at low effort in `versus.py` for a whole
  feature-parallel run (plan, parts, integrate, review);
- why `review-critical` and `test` pass under half their runs in real use (see below);
- whether a plan's parts at sonnet/high build as well as opus/high's (C).

**What a month of real use says** (one person's store over 30 days and several releases, 569 runs, 478 tasks):
the worker is 19% of the timed time and the verifier 3%; 52% is pickup (queued work waiting
for a dispatcher) and 23% `unnoticed` (a worker that died with nobody's session open to sweep it;
its longest runs, 60 to 80 hours, span weekends). `cauce stats` splits the pickup by cause; the board shows
the same from 0.51. The orchestrating session's own turns cost more than every worker together
($2,195 against $1,227 at API rates). By kind, `feature` passes first 41% of the time and costs
$9.16 per pass, `plan` 47% and $7.88, `review-critical` 25%, `test` 46%. The biggest lever left
is outside the worker: the time work waits before it starts and after it dies.

## Where the time went (this machine's store, before 0.45)

| Step | Minutes in all | What weighs |
|---|---|---|
| build | 472 | its worker (381) |
| fix | 177 | its independent verifier (44), its check (111 s per attempt at the median) |
| review | 111 | its worker |
| recheck | 66 | its worker (now decided by the fix's verifier where it answered every row) |
| refute | 35 | its worker |

Over 53 attempts that the independent verifier checked, cauce's check (p50 61 s) and the
verifier (p50 170 s) ran one after the other: 237 minutes. Run side by side, they would have
taken 66 minutes less.

## A: cauce's check beside the independent verifier (`overlap.py`)

The setup is a worktree of cauce at a real commit (`206ec54`), cauce's full suite as the check,
and a real verifier (`verifier_brief`, opus/high, read-only) on that commit's change. Each of
the three reps ran one after the other, as cauce did before 0.45, and then side by side, on a
machine with 4 CPUs.

| Rep | One after the other | Side by side | Check alone | Check beside the verifier |
|---|---|---|---|---|
| 1 | 792 s | 260 s | 262 s | 260 s |
| 2 | 822 s | 478 s | 270 s | 263 s |
| 3 | 1,235 s | 533 s | 260 s | 263 s |

The check was not slowed by the verifier beside it. The verifier passed in all six runs and
found the same things (2 to 3 findings). Side by side saved the whole check or more every time:
the median went from 822 s to 478 s (−42%).

cauce does this from 0.45: the `overlap` setting, `orchestrate.Ahead`.

## B: which cell gets a build done soonest, and right (`build.py`)

Each run is one worker on a fresh copy of the pricing engine, and hidden tests the worker never
sees judge the result. A build is right only when every hidden test passes. There were three
runs per cell for each build.

**Medium build:** three pricing rules, a receipt and a CSV export (7 hidden tests).

| Cell | Right | Wall p50 | Turns | Cost p50 |
|---|---|---|---|---|
| sonnet/high | 3/3 | 57 s | 6 | $0.14 |
| opus/high | 3/3 | 118 s | 10 | $0.43 |
| sonnet/xhigh | 3/3 | 170 s | 40 | $0.45 |
| opus/xhigh | 3/3 | 192 s | 24 | $0.77 |

**Harder build:** the same feature, plus moving 24 rules into a folder per stage and renaming
their methods everywhere (10 hidden tests).

| Cell | Right | Hidden tests | Wall p50 | Turns | Cost p50 |
|---|---|---|---|---|---|
| sonnet/high | 3/3 | 30/30 | 84 s | 12 | $0.23 |
| sonnet/xhigh | 3/3 | 30/30 | 276 s | 57 | $0.81 |
| opus/high | 2/3 | 29/30 | 189 s | 16 | $0.82 |
| opus/xhigh | 2/3 | 29/30 | 382 s | 49 | $1.72 |

More effort tripled the wall time and passed no more hidden tests. sonnet/xhigh, where every
feature started before 0.45, was right as often as sonnet/high, at 3 to 4 times its time. From
0.45 a feature starts at sonnet/high. A feature classified as high complexity starts a rung up,
and a repository's history and its calibrated standard still raise the start where its features
needed more.

## D and its cousin: starting what waits before its predecessor is verified

**Work held on a step whose verifier is still running.** No verified step in this store had
anything waiting on it in the current templates:
- A build or repair followed by a blind review runs no verifier.
- A fix's re-check is now decided by that same verifier.
- Work held with `--after` on another task happened once.

Not built.

**A review started before the build's own check finished.** The check failed 12 times in 50
after a worker claimed a pass. Starting the review early would save the check's median 65 s on
builds of 15 to 40 minutes, and throw away one review in four. Not built.

## C: how much effort a plan for parts needs (`plan.py`)

The plan step of `feature-parallel` was asked for the build of `build.py`, two runs per cell.
cauce's own parts reader (`launch.read_parts`, strict) judged each answer.

| Cell | Valid | Parts | Wall p50 | Cost p50 |
|---|---|---|---|---|
| sonnet/high | 2/2 | 4, 4 | 59 s | $0.18 |
| opus/high | 2/2 | 3, 3 | 93 s | $0.29 |
| opus/xhigh | 2/2 | 3, 3 | 189 s | $0.55 |
| opus/max | 2/2 | 3, 3 | 510 s | $1.56 |

opus/high, opus/xhigh and opus/max drew the same three parts (rules with checkout, receipt,
export). From 0.45 a plan starts at opus/high, where it started at opus/xhigh. sonnet/high split
the work another way (checkout apart from the rules). Whether those parts build as well was not
measured, so it is not the start.

## Where the time is now

Over this store's 1,148 minutes of runs:

| Phase | Minutes | What shortens it |
|---|---|---|
| the workers' own turns | 885 | the start cells: features at sonnet/high, plans at opus/high |
| the independent verifier | 171 | now beside cauce's check |
| cauce's check | 81 | now behind the verifier, wherever one runs |
| pickups | 30 | the lost wake-up, fixed |
| notes | 8 | |
| the plan | 1.5 | |

What is left is mostly each turn's model latency, which cauce does not set. Measured and not
built:
- skipping cauce's check when the worker ran the same command last: the overlap already hides it
  wherever a verifier runs, and the rest is about 4% of a build;
- reviews at lower effort: quality lost;
- splitting a review of a change with no parts by its folders: slower and dearer.

## E: the worker's own full check before it reports (`handoff.py`)

Worker transcripts on this machine (28 sessions, 13,123 s) spent 64% of their wall time waiting on
the model and 29% (3,793 s) in tests the workers ran themselves. Many of those runs were the whole
suite, 130 to 180 s each, three or four times in one task. The brief told a worker to run the near
tests as it goes and the full check "yourself once, at the end, before you report". Then cauce ran
the same check again.

The pricing engine got a slow suite: 12 more test files of 5 s each, 60 s in all. The worker,
sonnet/high, got cauce's own brief in two arms. `self` was the line before 0.47. `cauce` said:
"Do not run it yourself before you report: cauce runs it as soon as you do, and hands you its
failures to fix." cauce's check ran after the worker. A red check would have continued the
worker's session with its output, up to twice. Hidden tests judged each build.

| Build | Arm | Right | Green | Wall p50 | Worker's own full runs |
|---|---|---|---|---|---|
| medium | self | 3/4 | 4/4 | 216 s | 6 |
| medium | cauce | 4/4 | 4/4 | 131 s | 0 |
| harder | self | 3/3 | 3/3 | 208 s | 3 |
| harder | cauce | 3/3 | 3/3 | 152 s | 1 |

No run in either arm needed a second round, and none was less right without its own full run.
From 0.47 the brief says the `cauce` line.

## F: does the dispatcher's judgment hold independent work back (`dispatch.py`)

A queued writing task that is told to wait waits for the whole run of the work ahead, often
10 minutes or more. Haiku decides whether it starts beside that work, and its prompt said "when
unsure, answer false". Asked about clearly separate work (an invoice CSV export beside a profile page),
it waited 8 times in 8. Its reasons were "declares no surfaces" and helpers the two "might share".

Real `dispatch.decide` calls, 3 runs per pair. The pairs come in two sets. The tuning set has 14
independent pairs and 16 that collide (one needs the other's change, or both change the same
code). The held-out set has 6 and 6, written after the prompt was chosen, from real requests.

| Prompt | Set | Independent pairs started | Colliding pairs started |
|---|---|---|---|
| before 0.47 ("when unsure, answer false") | tuning | 29/42 | 0/48 |
| a wait names its collision | tuning | 42/42 | 1/48 |
| the same, and a result resting on behaviour the other changes is a collision | tuning | 42/42 | 0/48 |
| before 0.47 | held out | 14/18 | 0/18 |
| the last one | held out | 18/18 | 0/18 |

From 0.47 the dispatcher asks with the last prompt. A wait it gave is also asked again, at most
every two minutes, once the work ahead changed files it had not changed when the wait was
judged. The first judgment is often made when that work has just started and changed nothing.

## G: history kept raising where a task starts (`build.py`, the store)

A task's start rose to where half of the last tasks of its kind had passed. A task that started
high and passed there counted as a reason to start the next one as high, so a start history had
raised never came down, and the cells below were never tried again. In this machine's store:

| Kind | Passed where they started (last tasks) | Start history gave | Start from climbs only |
|---|---|---|---|
| feature | 11/14 | opus/high | sonnet/high |
| implement | 19/20 | sonnet/high | sonnet/medium |

`build.py` with the cell the fix leaves implement at, three runs per build, beside the cells
measured before:

| Cell | Medium build: right, wall p50 | Harder build: right, wall p50 |
|---|---|---|
| sonnet/medium | 3/3, 48 s | 3/3, 69 s |
| sonnet/high | 3/3, 57 s | 3/3, 84 s |
| opus/high | 3/3, 118 s | 2/3, 189 s |

From 0.48 only a climb raises a writing kind's start. A reading kind keeps the old count: its
pass is its answer, and `bench/review/effort.py` showed a review at lower effort missing the
hardest bug.

## H: an ending reaches the idle session sooner (the mod's pulse)

When work ended while the session was idle, the mod heard of it at its next poll, every 15 s
(`cauce endings` and the board: about 1.2 s of two processes each time). In this store the
mod's deliveries took 9 s at the median and 16 s at p90 from the ending. A task's ending now
touches a file beside the store, and the mod stats it every 2 s and polls at once when it
changed: within about 2 s plus the poll, with no process between endings.

## I: asking workers to make independent tool calls in one turn (`build.py`, `+batch`)

Worker transcripts here made 1.18 tool calls per turn, and 64% of a worker's wall time was the
model's own latency. Fewer turns could be faster. The `+batch` arm adds one line to the request:
make the calls that do not depend on each other in the same turn. sonnet/high, four runs per arm:

| Build | Arm | Right | Wall p50 | Turns p50 |
|---|---|---|---|---|
| medium | as briefed | 4/4 | 76 s | 5.5 |
| medium | `+batch` | 4/4 | 80 s | 30 |
| harder | as briefed | 4/4 | 100 s | 11 |
| harder | `+batch` | 4/4 | 111 s | 26.5 |

It was slower in both, so it was not built.

## J: filing notes off the critical path

A passing run filed what its worker learned (a Haiku call) before its `finished` event and before
its workflow advanced: 5.3 s at the median and 7.5 s at p90 over 107 runs in this store, on every
step of every workflow. From 0.49 a run files them after its ending and the advance; a
`notes_filed` event keeps the time it took.

## K: the independent verifier at medium effort (`bench/review`)

The verifier is 12% of this store's run time. At sonnet/medium it was faster (34 s against 58 s on
a small fix, 36 s against 51 s on the large change) but caught 20 of 42 planted bugs on the large
change where sonnet/high caught 27. Quality lost: not built (`bench/review/README.md`).

## L: the classifier's model call

A request no rule claims is classified by Haiku before its plan: 4 to 9 s, nearly all of a small
task's plan (`cProfile` on `orchestrate.plan`: 8.9 of 9.7 s). The rules claimed 94 of the 118
requests in this store and the model 12 (the rest predate the field), so it costs about one task
in ten a few seconds. The rules are deliberately not a keyword list for every request
(`classify.py`), so this is left as it is.

## M: cauce against one plain Claude Code session (`versus.py`)

The same request, repository and hidden tests for every arm. `cauce` is `cauce run … --verify 'make
test'` with a cauce home of its own (no history); the others are one `claude -p` at that cell
with the request as its whole prompt. Three runs per arm, four for the smoke rows.

| Build | Arm | Right | Wall p50 | Cost p50 |
|---|---|---|---|---|
| medium | cauce 0.49 | 4/4 | 89 s | $0.20 |
| medium | cauce 0.50 | 3/3 | 91 s | $0.19 |
| medium | opus/low | 4/4 | 87 s | $0.44 |
| medium | opus/medium | 3/3 | 98 s | $0.52 |
| harder | cauce 0.49 | 3/3 | 468 s | $1.43 |
| harder | cauce 0.50 | 3/3 | 213 s | $0.54 |
| harder | opus/low | 3/3 | 86 s | $0.59 |
| harder | opus/medium | 3/3 | 213 s | $1.29 |

Every arm was right every time. On the medium build cauce was as fast as one Opus session at low
effort and cost half as much. On the harder build cauce 0.49 started at sonnet/xhigh, one rung up
for a request classified high, and took five times as long. From 0.50 a writing kind classified
high starts at its ladder's first cell, as `build.py` showed it passing there as often.

The rest of cauce's 213 s, read from one run's events: its plan 6 s, the worker 105 s, the
independent verifier 50 s (the change touched a pricing checkout: a high risk), and filing notes
7 s after the ending, which a foreground `cauce run` still waits for. The verifier is the one
cauce gives that one session does not; the rest is the cell's own pace.

## N: where cauce's time goes against one session, and a guidelines CLAUDE.md (`versus.py`)

Pulling cauce apart on the harder build (three runs each, every one right):

| Arm | Wall p50 | Cost p50 |
|---|---|---|
| one session, opus/low | 86 s | $0.59 |
| cauce, start pinned at opus/low, no independent verifier | 91 s | $0.48 |
| cauce, its own start (sonnet/high), no independent verifier | 108 s | $0.27 |
| cauce as it runs | 213 s | $0.54 |

cauce's own machinery (plan, worktree, check, report) is about 5 s. The cell is about 17 s, at half
the cost. The independent verifier is the rest: the change touches a pricing checkout, a high
risk. Over 53 checks in this store it found blockers in 16, so it stays. A faster cell for it
was measured in `bench/review` (`effort.py`): sonnet/medium caught 20 and opus/low 18 of the 42
bugs sonnet/high's 27 cover, and opus/medium caught 36 in 81 s at three times the cost.

`andrej-karpathy-skills`' CLAUDE.md (think first, simplicity, surgical changes, verifiable goals),
committed in the copy, against the same sessions and cauce. All 33 runs were right; lines are what
the work added, at the median:

| Build | Arm | Wall p50 | Cost p50 | Lines added | Of them, tests |
|---|---|---|---|---|---|
| medium | opus/low | 84 s | $0.44 | 181 | 61 |
| medium | opus/low + guidelines | 75 s | $0.43 | 153 | 54 |
| medium | sonnet/high | 78 s | $0.27 | 261 | 125 |
| medium | sonnet/high + guidelines | 101 s | $0.34 | 253 | 144 |
| medium | cauce | 85 s | $0.20 | 226 | 104 |
| medium | cauce + guidelines | 99 s | $0.19 | 198 | 78 |
| harder | opus/low | 119 s | $0.82 | 341 | 164 |
| harder | opus/low + guidelines | 95 s | $0.69 | 310 | 139 |
| harder | sonnet/high | 152 s | $0.54 | 430 | 231 |
| harder | sonnet/high + guidelines | 156 s | $0.57 | 379 | 195 |
| harder | cauce | 192 s | $0.48 | 371 | 185 |
| harder | cauce + guidelines | 196 s | $0.49 | 357 | 166 |

The guidelines kept diffs 4 to 15% smaller, most of it in tests, and made opus/low faster; they
made sonnet and cauce no faster. Three runs a cell is noisy: nothing here was built from it.

## O: which model makes cauce's own small decisions (`delegate.py`)

The classifier and the dispatcher are Haiku calls. The same prompts and schemas, with only the
model changed, two runs each: the classifier on 36 requests labelled with the kinds that fit
them (the rules skipped, so this is the model's part alone), the dispatcher on `dispatch.py`'s 42
pairs.

| Decision | Model | Right | Wall p50 | Cost against Haiku |
|---|---|---|---|---|
| classify | haiku/low | 71/72 | about 6 s | 1× |
| classify | sonnet/low | 70/72 | about 6 s | |
| classify | opus/low | 72/72 | about 6 s | 20× |
| dispatch | haiku/low | 84/84 | | 1× |
| dispatch | opus/low | 84/84 | | 37× |

Opus was right once more in 72 at twenty times the cost and no faster: both stay on Haiku. The
classifier runs only for a request no rule claims, about one in ten here, and the session that
sends work already read the request: from 0.50 the orchestration guide and the mod's `queue`
tool tell it to pass `--kind`, which skips the call. Whether an intermediary pays when the
session itself is the same model as the worker is answered by M and N: a session at opus/low on
its own took 86 to 96 s on the harder build; cauce pinned to that cell with no verifier took
91 s. The intermediary costs about 5 s; what it adds is the check, the worktree and the record.

## P: one build as two tasks side by side (`versus.py`, `cauce-split`)

The medium build as the two tasks a session would send at once (the pricing rules; the receipt
and the export), each with its kind, merged after. Three runs:

| Arm | Right | Wall p50 | Merge conflict |
|---|---|---|---|
| cauce, one task | 3/3 | 88 s | |
| cauce-split, two tasks | 7/7 hidden tests | 113 s | none |

Slower, and the repository's own tests failed after the merge, though each branch passed alone
and the hidden tests passed (why was not dug into: the receipt's half reads the discounts the
other half adds). Splitting a build whose halves read each other's change is not worth it; `route.split_first` already asks for a
split only for builds of several independent pieces.

## Q: a start at Opus low effort, with the verifier (`versus.py`, `cauce@opus/low`)

| Build | Arm | Wall p50 |
|---|---|---|
| medium | opus/low, one session | 87 s |
| medium | cauce pinned at opus/low, with the verifier | 209 s |
| harder | cauce pinned at opus/low, no verifier | 91 s |
| harder | cauce pinned at opus/low, with the verifier | 259 s |

Opus at low effort counted as a cheap cell, so a medium-risk change it made called the verifier,
and two of the three medium builds climbed to opus/high on what it said, though every arm at
opus/low passed every hidden test on its own. From 0.51 a cheap cell is Haiku or a model below
Opus at low effort.

The verifier's own cell on `bench/review`'s large change (42 planted bugs, `effort.py`):

| Verifier cell | Caught | Wall p50 |
|---|---|---|
| sonnet/high (as it runs) | 27/42 | 51 s |
| sonnet/high, 20 turns | 30/42 | 67 s |
| sonnet/medium | 20/42 | 36 s |
| opus/low | 18/42 | 36 s |
| opus/medium | 36/42 | 81 s, $0.45 |

A turn cap saved nothing. The faster cells missed a third of what high catches. In this store
the verifier found blockers in 16 of 53 checks, at 19 turns p50 and 33 p90: it stays where it is,
and moves off the critical path instead (R).

## R: the independent check after the ending (`versus.py`, 0.51)

From 0.51 a pass that cauce's own check settled ends at once, and the verifier reads the kept
branch after it (`late_verifier`). The wall time below ends when `cauce run` exits; the late check
is waited for apart. Three runs per build, every one right on the hidden tests:

| Build | cauce 0.50 | cauce 0.51 | Late check after the ending | Cost p50 |
|---|---|---|---|---|
| harder | 203 to 213 s | 122 s (114 to 136) | 66 to 108 s | $0.47 |
| medium | 88 to 91 s | 82 s (78 to 88) | none: no verifier needed | $0.18 |

On the harder build one late check in three found a blocker in work the hidden tests passed and
reopened it as `review`: a false alarm, answered by a resume that gives the worker the blocker.
Before 0.51 the same blocker earned a correction round before the ending, which costs the same
worker time but held every run's ending for it. Whether reopenings like this are rare or common
in real use was not measured (see the summary's "never measured").

The first measurement of this lost every late check: the detached work was a `fork` of the run,
whose SQLite connection does not survive one, and the child's writes vanished when it closed. It
is a fresh process now; the bench caught what the unit tests, which run it in-process, could not.

## S: a cheaper cell for `refactor` and `test` (`kinds.py`, 0.62)

Real workers, three runs per cell, on fresh copies of the memory bench's pricing engine
(`bench/memory/hard`). `refactor` renames the rule methods and moves each rule module by its
stage: right only when all five checks hold (the new layout, the old names gone, and a set of
carts priced exactly as the untouched engine prices them). `test` writes tests for the money and
line helpers: right only when they pass, no source changed, and they kill all eight mutants. On
the untouched engine the judges give 2/5 and 2/8.

| kind | cell | right | held | wall p50 | turns p50 | $ per right |
|---|---|---|---|---|---|---|
| refactor | haiku/high | 3/3 | 15/15 | 113 s | 24 | 0.020 |
| refactor | sonnet/medium | 3/3 | 15/15 | 21 s | 6 | 0.104 |
| test | haiku/high | 3/3 | 24/24 | 134 s | 25 | 0.030 |
| test | sonnet/medium | 3/3 | 24/24 | 27 s | 8 | 0.110 |

Haiku was as right as the first rung of both ladders, at a fifth of the cost per right answer,
and about five times slower: four times the turns. That is enough to *try* it, not to start
there: `matrix.PROBATION` now holds Haiku below `refactor` and `test` as it did below
`implement`, so each repository tries it in turns with the first rung, and it starts there only
where its first tries pass as often. Three runs per cell are a small sample; the trial, not this
table, decides.

## T: the diagnosis method on an unclear bug (`methods.py`, 0.63)

Real Haiku workers (haiku/high), four runs per arm, on fresh copies of the pricing engine with one
planted bug, half-even rounding where the engine rounds half up, told only by its symptom: "some
order totals come out a cent off, but only sometimes". The arms are the same request with and
without the diagnosis protocol cauce briefs `debug-unclear` workers with. A run is right when the
suite passes, the prices are the engine's, and no test was touched.

| arm | right | wall p50 | turns p50 | $ p50 |
|---|---|---|---|---|
| with the diagnosis | 4/4 | 100 s | 22.5 | 0.026 |
| without | 2/4 | 76 s | 27 | 0.020 |

Both misses without it claimed a pass: they changed something and stopped, the cause still in
place. With it every worker reproduced the failure first and fixed the rounding mode. Four runs a
side is a small sample, so the method stays on trial per repository (`methods.arm`); this is why
it starts in its trial instead of being left out until one proves it.

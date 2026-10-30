# Code coverage, one report, and mutants

## Which code each step ran: `qweave -cover`

```sh
qweave -cover [-coverpkg your/module/pkg] go test -run TestX ./...   # go install github.com/chucklehead-dev/gotogether/qweave/cmd/qweave@latest
```

```go
x := sys.Explore(t, qtest.ExploreConfig{Seeds: 30}) // sys is a qtest.System; coverage is collected when woven
t.Log(x.Evidence().Code) // never run, run by no step, outcomes that ran the same code
```

- Skip the test when `len(qcover.Blocks()) == 0` (not woven).
- "Never run" after a conforming exploration: an error path whose fault
  was never taken (check `x.Evidence().Faults`), code the model's environment
  rules out, dead code, or a scenario the model does not describe.
- "Run by no step" is code no step of its own task explains: clients
  whose steps the services record, relays, setup, or work after a task's
  last step. A worker's code there means a missing step.
- Two outcomes of an action that ran the same code: the model tells them
  apart and the code does not. That is fine when the outcome is the
  environment's (a lost response), and a question when it is the code's.

## A real environment's coverage against the simulation's

Build the real environment's binaries with `go build -cover`, run them
with `GOCOVERDIR=dir`, and compare with a woven simulation's: run its
tests with `GOTOGETHER_EVIDENCE=dir` and pass an exploration's evidence
(or a summary written from `x.Evidence().Code`):

```sh
gotogether cover -covdir run1,run2 -sim evidence/_/TestFaithful/x1.json
```

## What no test of the suite tried

Each exploration's Evidence says what its own runs left out; a suite's
tests may cover each other. Export a fresh `GOTOGETHER_SESSION=$(uuidgen)`
for each suite invocation, then run `GOTOGETHER_EVIDENCE=dir go test -count=1 ./...`
(each exploration writes `dir/<package>/<test>/x<N>.json`, its format and role in
it; a test's first exploration clears what earlier runs left), then

```sh
gotogether evidence dir            # each exploration's verdicts, then the gaps
gotogether evidence -strict dir    # exit 1 on a gap (for CI)
gotogether evidence -expect checks.txt dir   # exit 1 naming a listed test or exploration that wrote none
```

Keep the session variable set for the evidence command. Files with another
session or no session are excluded. Use `-history` with the variable unset
to aggregate historical evidence; it cannot establish current-run completeness.
Never reuse a session ID; concurrent invocations need separate directories.

The gaps count faithful explorations only: one of a `System` whose
`Mutant` names its bug (a config's mutation), Mutate's mutant runs and
qhegel's replays are listed, not counted, since a mutant takes paths the
system does not.

A gap is a model action no test took (by model), a declared fault point
no test reached, or a fault kind reached and never faulted.

"Real only" is code the simulation never leads to (a fault its doubles
do not inject, a path they do not take): its verdicts say nothing about
it. "Simulation only" is what the real runs did not exercise. Go's
counters are per process, so the real side has no per-step attribution.

## Dead code, and error paths never tried

`actionmap` (qanalysis) has the call graph: `go run ./cmd/actionmap ./...`
lists dead functions (no main, init or exported API reaches them). With a
summary and the runs' fault coverage, `actionmap.UntriedErrorPaths(m, s,
x.Evidence().Faults)` lists the blocks no run ran in the callers of a fault point
the runs reached but never faulted: its error handling. Untried, not dead:
raise the kind's rate or script it first.

## One report: `x.Evidence()`

`t.Log(x.Evidence())` (an exploration, or a sweep's `SweepResult`) says in a few
lines what the runs show: verdicts by reason, fault kinds faulted and
pairs together (and those never faulted), the code run (when woven
with `-cover`), and mutants killed (set `Mutants` from
`sys.Mutate`). Read it after a green test: it is what "conforms" leaves
unsaid.

## What the model constrains: mutants (`qweave -mutate`, `System.Mutate`)

```sh
qweave -mutate -coverpkg your/module/pkg go test -run TestMutation ./...
```

```go
rep := sys.WithRates(crashy).Mutate(t, qtest.ExploreConfig{Seeds: 20}) // skips unwoven
t.Log(rep.Evidence()) // the baseline's verdicts and faults, with the mutants
rep.Expect(t, qtest.NoSurvivors("(Payer).Pay: drop call: ack()")) // equivalent ones marked, as a survivor's report prints them
```

- Every mutant (a negated `if`, a moved comparison boundary, a dropped
  call) is in one build; each is explored with the seeds, verdicts shared.
- A survivor is code the model does not constrain. Ask, for each: is it
  equivalent (a dropped ack the environment redelivers anyway), is the
  effect unobserved (a step records nothing the model compares: add the
  field and an `expect` to the binding), or is the code not needed?
- Checkout's first run had a cancel that forgot to restock survive: no
  step carried the stock. Recording it and an `expect: 'stock ==
  {{.obs.stock}}'` killed it.
- A step whose absence no run's check can see (the client's "done") is
  a claim over runs: give it to the report's Expect, `sys.Mutate(t,
  cfg).Expect(t, qtest.PerMutant(qtest.Takes("done").InAtLeast(0.9)),
  qtest.NoSurvivors(...))`. The baseline must meet it, and a mutant that
  does not is killed (Killed and Survived say so after Expect). A mutant whose runs record nothing at
  all is killed too.
- examples/hello's `TestMutationOfTheCounter` ends in `NoSurvivors` with
  three marked equivalent, each with its reason. Its first run had a
  client that sent two requests of three survive: nothing said the
  client finished. A `done` action (every request applied) and the
  `Takes("done")` claim killed it.
- Unreached mutants are coverage's: no run reached their code.

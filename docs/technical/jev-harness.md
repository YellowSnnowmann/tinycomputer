# The Jev harness

This page is the map. It shows every layer between a caller's request and a
Jev evaluation, what each layer adds to the request, where the time goes, and
how each layer is tested and observed. [`decision-loops.md`](decision-loops.md)
goes deep on the flow runtime's loops and thresholds; this page is what to
read first, and what to read when you are trying to make the loops faster.

## Jev in one paragraph

Jev is TypeSafe's decision model. The engine reaches it through the
`tinyinference_decisions` client in `vendor/tinyinference` (fix the client
there, not here). A request carries one shared `state` value and a map of
questions, each a **Noul** (yes/no, answered as a probability), a **Score**
(an ordered scale, answered as a distribution over levels), or a **Choice**
(labelled options, answered as a pick plus a distribution). Jev never writes
text and never plans. Every question in one request is answered from the
same state, independently, in one round trip.

## The stack

```text
caller (agent, host, lab)
  │  TinyBus member: RunFlow / RunGoal / ResolveIntent / StartTask …
  ▼
crates/tinycomputer/src/tinybus_module/     dispatch/, runner.rs
  │  holds the configured JevRuntime; tasks get a per-task Workspace
  ▼
crates/tinycomputer-engine/src/
  task/                  the task controller: runs flows in the background,
  │                      pauses for input and approval, splits the budget
  ▼
  agentic/flow/          run_flow → FlowRun (mod.rs): the step driver
  │                      (run.rs), budgets, look / explore (look.rs),
  │                      act (action.rs), and ask() (decide.rs)
  ├─ steps/              one function per step kind
  ├─ act/                the `do` loop: judge, recover, move
  ├─ ground/             one element for a purpose
  ├─ enter/              slots to fields, verified delivery
  ├─ wide/, survey.rs    the wide strategy: one request per turn, the survey
  ├─ ledger.rs           the working memory wide questions see
  └─ ask/, vote.rs       question builders; framings and merging
  ▼
  agentic/runtime.rs     JevRuntime::evaluate — the one door every call
  │                      goes through; the debug journal hooks in here
  ▼
vendor/tinyinference     tinyinference_decisions::Client: HTTP, retries,
                         timeout, response validation
```

`RunGoal` and `ResolveIntent` (`agentic/goal.rs`, `agentic/task/`,
`agentic/resolve.rs`) sit beside
the flow runtime rather than under it; they share only `JevRuntime` and its
error mapping.

## The three loops

| Loop | Entry | Shape | Read more |
|---|---|---|---|
| Intent | `resolve_intent` | one observation, one decision (operation + target), an optional rerank, an optional action | `agentic/README.md` |
| Goal | `run_goal` | per turn: observe, check the caller's visible success predicates, decide one operation and target, re-observe the target, act once, observe again; consequential actions return a one-use confirmation handle | `agentic/README.md` |
| Flow | `run_flow` | per step: the step kind's own logic, built from many small decisions — the `do` loop, grounding, slot matching, condition checks | [`decision-loops.md`](decision-loops.md) |

The goal loop asks one large question per turn and never lets Jev judge its
own completion; only the caller's accessibility predicates end it. The flow
loop asks many small questions and lets calibrated Jev judgements end steps.
Flows are where the product is going; the goal loop is the baseline the lab
measures them against.

## The life of one flow decision

Every flow question reaches Jev through `FlowRun::ask`
(`agentic/flow/decide.rs`), or, for several independent requests at once,
`FlowRun::ask_batch`, which runs the steps below for each and sends every
framing of every request together: one round trip. In order:

1. **Build.** A step's code builds the questions (`ask/questions.rs`) and the
   shared state (`ask::state`, in `ask/screen_state.rs`: app, window, surface, current step, visible text,
   up to 120 elements, the last eight history lines, and field contents when
   `include_values` is set). Screen text is always wrapped as
   `untrusted_accessibility_data`.
2. **Budget.** The run's call budget is checked first; a spent budget stops
   the run with `ModelBudget`.
3. **Page kind.** On the browser, a `page_kind` Choice rides along, and its
   answer briefs the *next* request ("a results page", "a form").
4. **Brief.** Questions that *choose* — which element, move, field, record,
   and the `confirm` Noul — get the run's brief: the goal, whom it is for, the
   plan with the current step marked, what has been chosen so far, the page
   kind. Questions that *judge* the screen are left unbriefed; measured, a
   brief pulled "is the search done?" from 0.75 to 0.39 because Jev judged the
   step against the whole task.
5. **Mask.** Every secret's value is replaced by `${name}` anywhere in the
   state or the questions. Nothing after this point, including the journal,
   sees a secret.
6. **Split and fit.** A request over 48 KB of JSON (`MAX_REQUEST_BYTES`)
   is cut by its questions into parts asked at once, each with the whole
   state (`decide::split`); their answers merge back by question id. A
   state that alone takes more than half the limit first loses the tails of
   its longest lists, so each part still holds several questions. A part
   still too large is shrunk: the brief is kept on one question only, then
   the longest element and text lists lose their tails. A decision asked in
   parts costs a call per part and framing, and the budget is charged for
   each: a speculative request that would run past it is left out, and the
   first asks fewer framings instead. Jev rejects requests
   past its token limit outright, and the Tiny Humans gateway's limit is the
   lower one (57 KB passed, 68 KB came back HTTP 502).
7. **Frame.** `vote::framings` makes `votes` copies (default 7, at most 9):
   label-keyed Choices are shuffled and relabelled, and each copy gets a
   different one-line perspective. Framing 0 is the request as built.
8. **Evaluate.** All framings go to `JevRuntime::evaluate` at once, each on
   its own task. Each call is charged to the budget.
9. **Merge.** Answers are mapped back to the original keys, kept per
   framing as each question's ballot (`vote::ballots`), and averaged
   (`vote::tally`). A Choice's `confidence` becomes the share of framings
   that agreed with the winner.
10. **Record.** The merged exchange goes into the result's `trace` when the
    request set `trace: true`; each raw framing, and the decision's wall
    time, go to the debug journal when it is on.

The step's code then thresholds the merged answers (see
[`decision-thresholds.md`](decision-thresholds.md)). A deliberating run
first reads the ballot's evidence — lead and agreement, not one number — and
when it is thin asks again: more framings (`FlowRun::widen`, which joins the
same ballot), a duel, a contrast, other views of the screen
([`specs/jev-deliberation.md`](specs/jev-deliberation.md)). Every rung goes
through the same door, so steps 2–10 apply to each.

## Where the time goes

A step is a sequence of waits. Within one, the framings of a decision run
in parallel, and so do decisions that do not depend on each other
(`ask_batch`). One `do` turn is roughly:

```text
look (observe)  →  judge + ground's first round (1 round trip)  →  [ground (0+ rounds)]  →  act  →  settle
```

Two narrow-strategy decisions are batched:

- **A step's first turn** asks the judge and grounding's first round for an
  `activate` move together: before anything is done a step almost always
  activates, and the target's pool and purpose do not depend on the judge.
  If the judge picks another move, that round's calls were spent for
  nothing. Later turns are not speculated on: after an action the judge
  most often ends the step.
- **Narrowing** asks the region question and a knockout cut along the
  regions together, instead of up to three region rounds and then a
  knockout.

On a crowded page that takes an `activate` turn from up to five round trips
(judge, two regions, knockout, Choice) to two (judge with region and
knockout, Choice). So a turn's wall time is the observation, plus each
round trip's *slowest* framing, plus the action, plus settling. The levers:

| Lever | Effect on latency | Effect on accuracy |
|---|---|---|
| `strategy` | `wide` asks one request per `do` turn instead of two to seven in sequence | the digest, survey, and memory show more of what matters; measure with the lab's `--strategy` |
| `votes` | a decision waits for its slowest framing: more framings, longer tail; a framing slower than 2.5 s (3.5 s at 32 KB or more) gets a copy, and the first answer counts | more framings average out position and phrasing bias |
| request size | Jev's latency grows with input tokens; a big element list is the usual cause | trimming can drop the element that was needed |
| grounding memory | a remembered element is confirmed with one Noul instead of narrowing | none when the hint is right |
| `disabled_loops` | each loop off removes a question or a whole decision | measure it before shipping it off |
| `settle` | fixed per action on the desktop, network-idle on the browser | too short and the next look sees the old screen |
| observation | an accessibility snapshot of a large window is slow; `explore` adds more | a budgeted view can miss the target |

Measure before changing any of them. The debug journal
([`jev-journal.md`](jev-journal.md)) times every observation, action,
decision, and call, and `jev_journal` summarises a run into exactly this
breakdown.

## Configuration

`JevRuntime::configure` builds the client from the module's private `jev`
configuration: the provider (`type_safe`, `open_router`, or
`tinyhumans_openrouter`), the key, an optional endpoint (only the approved
URL for that provider is accepted), `timeout_ms`, `max_retries`, and the
model, `jev-latest` by default. The runtime is cheap to clone: the client,
the pending-confirmation table, and the journal are shared behind `Arc`s.

## How it is tested

| Harness | Where | What it is for |
|---|---|---|
| Flow simulator | `agentic/flow/flow_tests.rs`, fixtures `flow_tests/simulator.rs`, `oracle.rs`, `screens.rs` | a scripted mail app and booking widgets, plus an *oracle* Jev that answers from the simulator's true state; every loop behaviour and regression lands here first |
| Mock evaluator | `agentic/agentic_tests.rs` | queued, canned `EvaluationResult`s for the goal and intent loops; records every request for assertions |
| Fake runners | `task/task_tests.rs` | a `FlowRunner` that returns scripted replies, so the task controller is tested without a surface or Jev |
| The lab | `crates/tinycomputer-examples`, `scripts/lab` | the built module, loaded like production, driving real applications with real Jev; see [`lab.md`](lab.md) |

The simulator and the mock both implement the private `Evaluator` trait that
`JevRuntime` holds, so every test goes through the same `evaluate` door as
production, journal included.

## How it is observed

| Level | Turned on by | Holds | Lives |
|---|---|---|---|
| Step reports | always | per step: outcome, note, turns, calls, actions, loops, lowest confidence | the `RunFlow` result |
| Trace | `trace: true` on the request | per decision: the state, the questions, the *merged* answers | the `RunFlow` result; the lab writes it to `jev.jsonl` |
| Debug journal | `TINYCOMPUTER_JEV_JOURNAL`, or `JevRuntime::with_journal` | per call: the exact request and raw answers, latency, attempts, tokens; per decision, observation, action, and step: wall time | `.jev-journal/<run id>/journal.jsonl`, git-ignored |

The trace answers "what did the run decide?"; the journal answers "what
exactly went over the wire, and how long did everything take?".

# Decisions

One line (or short block) per design decision, newest phase last. If you deviate from something
here, add a new entry rather than editing an old one.

## Phase 0 — repo and core kit (2026-10-18)

### Approved before coding

1. **Simulated time crosses the service boundary as a header.** Services are separate FastAPI apps
   and cannot share a Python clock, so they are told the episode's current simulated time on every
   request via `X-Sim-Time` (`kit.service.SIM_TIME_HEADER`) and never read a clock themselves. A
   service called without the header raises rather than guessing. In tests and CI services are
   mounted in-process over ASGI — fast, no ports, no races; docker-compose profiles are the
   alternate multi-process mode.
2. **Failure-type ids are namespaced** `<world>.<name>` (`payments.overspend`,
   `security.late_escalation`), with the kit owning `kit.unauthorised_action`, `kit.incomplete` and
   `kit.other`. Three worlds would otherwise collide on names like "late submission"; the
   leaderboard shows the short label.
3. **`state_diff` is emitted by the service** that performed the change, as
   `{op, path, before, after}` entries. The kit does not diff snapshots: it would be slow and would
   report noise instead of the rows the tool touched.
4. **"Graders never see the agent's reasoning" is a type, not a convention.** `Grader` receives a
   `GraderTrace`, whose steps have no `agent_message` field at all. `Trace.grader_view()` is the
   only way to produce one.
5. **`FailureTypeDef.high_impact` replaces payments-specific wording.** The scorer's "clean run"
   metric is "zero high-impact failures", so the kit needs no notion of money.
6. **Import roots are exactly those in the build plan**: `kit`, `runner`, `stress`,
   `worlds.<name>`. Distributions are `agent-sandbox-kit`, `-runner`, `-stress`,
   `-world-payments`, `-world-security`, with the umbrella `agent-sandbox` providing the `sandbox`
   CLI. Revisit before tagging `kit-v0.1` if the top-level `kit` name is a problem on PyPI: it is
   free to change now and expensive afterwards.

### Decided while building

7. **OpenEnv is an optional extra, pinned to `openenv==0.9.0`.** `meta-pytorch/OpenEnv` redirects
   to `huggingface/OpenEnv`; v0.9.0 is current. It is experimental upstream and pulls a large
   dependency tree (`harbor[...]` on Python 3.12), so `kit` must not depend on it: the adapter
   imports it lazily inside `environment_class()`, which is why the `Environment` subclass is built
   by a factory rather than declared at module level. Install with
   `pip install 'agent-sandbox[openenv]'` or `just setup-openenv`.
8. **The kit's `Episode` keeps its own `StepResult`; the adapter maps it to OpenEnv's shape.** In
   openenv 0.9.0 `step()` returns an observation carrying `done` and `reward`, not a tuple. The
   adapter also implements the optional `TaskProvider` protocol structurally, so a world's task
   sets become selectable splits (`payments-v0.1`, `payments-v0.1-hidden`).
9. **Rewards are computed inside the environment, as OpenEnv expects**: when an episode finishes,
   the adapter runs the task's grader and reports its score as that step's reward. No LLM-judge
   reward.
10. **`WorldSpec` carries `tasks_dir`** so the runner can find a world's packaged public tasks
    without importing the world. Added during Phase 0, before the interface freeze.
11. **A `WorldSpec` registers its failure types when it is constructed**, not when the registry
    loads it, so a grader can emit `hello_world.overshoot` in a unit test that never touches the
    registry.
12. **An unknown tool reports `unknown_tool`, not `tool_not_allowed`.** Calling a tool the world
    does not have is a mistake, but it is not an unauthorised action, and the two are counted
    differently.
13. **The hello-world example lives at `kit/src/kit/examples/hello_world/`**, not `kit/examples/`
    as the build plan sketched, so it is importable as `kit.examples.hello_world` and can be
    referenced by an entry point and by `grader:` paths. It deliberately uses no web framework, so
    discovering worlds never requires one.
14. **`AsgiService` drives the ASGI app through `asyncio.run` per request.** httpx 0.28 removed
    synchronous ASGI transport. Episodes are single-threaded and synchronous — that is part of what
    makes them reproducible — so one loop per request is acceptable; revisit in Phase 9's scale
    work.
15. **`mypy --strict` covers `kit/src/kit` only**; the rest is checked non-strictly. Packages ship
    `py.typed` so worlds and the runner see the kit's types.
16. **Each tool call advances simulated time by `BaseEpisode.step_seconds`** (default one second),
    so deadlines and SLAs mean something even in a world with no other scheduled events.

### Open, to settle before `kit-v0.1` is tagged

- Whether to namespace imports under `agent_sandbox.*` (decision 6).
- Reward shaping beyond the grader's score: currently the adapter reports `score` and nothing else.
- Whether `Trace` should carry per-step token usage for scheduled events (it currently does not).

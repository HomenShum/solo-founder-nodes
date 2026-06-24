# Solo Founder Agent Builder + Eval Loop Engineering Skill Nodes - prove your agent works, in your app, without cheating

This one skill is the whole loop. The master directive runs the phases in order, reading the matching
**playbook in `nodes/`** when it enters each phase (progressive disclosure). It is
**benchmark-driven development for agents**: define what *good* looks like with a real benchmark and
rubric **before** building, then build the agent and UI/UX to pass it **in the actual app, on the real
UI**, and prove the capability is real, not memorized.

## The one non-negotiable - why this skill exists

A coding agent told to "pass the benchmark" will cheat: hardcode answers, detect-and-template
specific tasks, report a high score with **zero** real capability. NodeRoom has receipts for the
failure pattern: selected/family-writer benchmark paths around **0.96**, an older pre-materializer
signal around **0.009**, and a current full-100 clean-probe mean of **0.251875**. Treat the exact
"0.96 versus 0.008" launch-copy sentence as **unproven until the incident bundle is linked** in
`docs/PUBLIC_CLAIM_PROOF.md`. This directive is the honesty conscience a solo founder cannot staff.

Every phase obeys:
- **HELD-OUT** - never tune on the tasks you score on; keep a held-out split + an off-distribution slice.
- **NO ANSWER-KEYS** - no per-task detectors or hardcoded outputs; revert any change that only lifts the tuned tasks. The **honest lane** sharpens this: the same task scores three ways and conflating them *is* the bug. **model-off** (0 tokens, no real tool-call) is a degenerate floor / harness failure, NOT capability. A **task-specific / family writer** firing (deterministic `detect-task -> emit-canned-package`) is an answer-key, fake. Only **model-in-loop + the generic writer** is the real signal. **NON-GENERAL GUARD:** a run counts as capability IFF the generic writer alone produced output, the model was genuinely in the loop (tokens > 0 / real transport), AND it ran on a held-out task; otherwise tag it `answer-key | model-off | replay` and exclude it. Run **clean-probe mode** (force the generic writer; a 0-token trial FAILS LOUDLY; held-out n >= 10; report the distribution). A change counts only if it raises the held-out clean-probe mean via a reusable tool / context-management / generic-writer / app-UI affordance, never a per-task writer. **ENFORCE, DON'T REQUEST:** the substrate must **DERIVE** the gate (which writer fired, model-in-loop, held-out membership) from observed evidence and never accept self-reported fields; a self-set clean-probe flag is itself an answer-key. Red-team the substrate itself as a recurring phase; the claim is "cheating is detectable and expensive," never "impossible." Full doctrine: [`references/honest-lane.md`](references/honest-lane.md).
- **IN-APP TRANSFER** - a score counts only if the same task through the real app UI reproduces it (browser-verified).
- **HONEST PROVENANCE** - every number traces to a recorded run; report the real number even if it is low.

## Who acts / how the human steers

The user's coding agent drives each phase (reads the codebase, web-searches, builds). The user steers
by **comment**. If the user defers, proceed on explicit, stated assumptions and surface them.

**Full autonomy (the goal).** Under a founder **autonomy policy** ([`references/autonomy.md`](references/autonomy.md))
- model + key, a budget cap, a download allowlist, auto-approve installs/code - the agent runs the
WHOLE loop unattended on the founder's behalf: download the dataset, wire the harness, run the model,
verify in the live app, and iterate from proof failures, pausing only on a hard-stop (over budget, untrusted download,
public publish, deleting data, credentials). The carve-out that makes this safe: **the agent does
every step and produces every proof, but never grades / seals / verifies itself - the referee (seal
salt, gate derivation, sealed-gold, independent verifier) lives out of its reach**
([`references/trust-root-api.md`](references/trust-root-api.md)). Maximum autonomy on the work; zero
autonomy on the scoring.

## Permission gates (hard)

Phases that install heavy infra (Docker, Harbor, HuggingFace), spend API money, or mutate the codebase
are **guide -> generate -> gate**: present the plan + exact commands + links, dry-run if possible, and
get explicit approval **before** executing.

## External setup gate (hard)

External accounts, billing, OAuth, production deploys, storage projects, and API keys are human gates,
but they are not permission to stop early. Before pausing on a provider key or service setup, complete
all deterministic prework that does not require the secret: adapter boundary, AI chat component, typed
chat action protocol, server-side secret env names, missing-secret UI, blocked-path test, setup
documentation, cost/latency ledger shape, and exact resume commands. Do not expose provider keys
through `VITE_`, `NEXT_PUBLIC_`, screenshots, logs, or chat. The pause receipt must say what is
already built, what human action is required, and which command resumes proof collection. Template +
verifier: [`templates/setup/externalSetupGate.ts`](templates/setup/externalSetupGate.ts); CLI:
`npm run sfn -- setup gate ...`.

## Optional agent host setup (OpenRouter / OpenClaw / Hermes)

Do not lock the skill to Claude Code, Codex, OpenClaw, Hermes, or any model provider. If the founder
wants a low-cost OpenRouter-backed agent-host setup, generate an **optional** setup pack with
`npm run sfn -- agents openrouter-audit --out openrouter-model-audit.json` followed by
`npm run sfn -- agents openrouter-plan --audit openrouter-model-audit.json --out agent-host-setup`.
The pack must keep secrets out of repo files, cite the OpenRouter model catalog date, and select
models by evidence:

- OpenClaw default: cheapest paid conformance-proven route (`deepseek/deepseek-v4-flash` in the
  2026-06-24 audit).
- Hermes default: conformance-proven coding fallback (`qwen/qwen3-coder-next` in the 2026-06-24
  audit).
- Free and multimodal catalog lanes stay in `SOLO_OPENROUTER_AUDITED_*` until the selected host
  produces its own smoke and conformance receipts.

Treat model choice as a receipt-backed policy, not a hardcoded eternal truth. If the catalog changes,
rerun smoke + agent conformance before changing claims.

## CLI command center + universal event bus (hard)

The clean visualization is the CLI command center, not a static diagram. Use
`npm run sfn -- dashboard --project <path>` to show loop state, active proof status, agent hosts,
runtime, metrics, artifacts, and recent events. The slogan is binding:
**Hooks observe the agent. Receipts prove the work. The CLI makes the whole loop visible.**

All agent hosts normalize telemetry into the universal `SoloEvent` bus in `.solo/events.jsonl`:
`session.start`, `session.stop`, `phase.start`, `phase.stop`, `prompt.submit`, `tool.pre`,
`tool.post`, `tool.error`, `file.read.pre`, `file.write.pre`, `file.write.post`,
`command.run.pre`, `command.run.post`, `browser.proof.start`, `browser.proof.stop`,
`receipt.write`, `memory.write`, `eval.start`, `eval.stop`, and `rework.recorded`. Native hooks are
allowed when a host supports them; otherwise use the external proof wrapper. Generic/no-hooks agents
must not self-report completion. Install or inspect adapter plans with
`npm run sfn -- agent matrix` and
`npm run sfn -- agent install-hooks --target <codex|claude-code|windsurf|devin|cursor|trae|openclaw|hermes|generic|all> --project <path>`.

NodeRoom proof runs are surfaced through `npm run sfn -- noderoom run-fresh-room ...`, but a handoff
receipt is not a pass. Only verified fresh-room receipts, trace/video artifacts, visual recording
checks, and a passing proof verdict count. Doctrine: [`references/cli-command-center.md`](references/cli-command-center.md);
copyable implementation: [`templates/events/`](templates/events/) and
[`templates/dashboard/`](templates/dashboard/).

## Context substrate + control plane (required for full autonomy)

The agent must not rely on chat context alone. At `discover`, build or refresh a graph-context receipt
for the app (`graphify-out/GRAPH_REPORT.md` + `graphify-out/graph.json`, or an equivalent code graph).
From `benchmark` onward, fail closed if the receipt is missing or stale. Query the graph before raw
grep/read for architecture, adapter, UI, benchmark, export, persistence, or scorer questions. Store
the receipt and important query refs in memory, never held-out task contents. Doctrine:
[`references/context-substrate.md`](references/context-substrate.md); copyable inspector:
[`templates/context/`](templates/context/).

Run the loop through a durable control plane when unattended: one loop id, phase checkpoints, approval
requests, trigger idempotency, budget/spend, trace spans, worktree leases, and improvement candidates.
This is how the agent pauses/resumes, survives a fresh session, and hill-climbs from observed failures
instead of waiting for the founder to steer. Doctrine: [`references/control-plane.md`](references/control-plane.md);
copyable implementation: [`templates/control/`](templates/control/). The control plane coordinates
work; `SoloLedger` and the trust-root still derive the benchmark verdict.

For resumable phase enforcement, create a RALPH loop ledger with
`npm run sfn -- loop init --goal <goal> --project <path>`, inspect it with
`npm run sfn -- loop status --project <path>`, resume with
`npm run sfn -- loop resume --loop-id <id> --project <path>`, and start anywhere only through
`npm run sfn -- loop start --from <R|A|L|P|H> --project <path>`. The ledger writes
`.solo/loop-state.json`, `.solo/events.jsonl`, `.solo/receipts/<milestone>/`, `.solo/proof-verdict.json`,
and `.solo/rework-ledger.md`. A milestone can start only if prior required receipts exist; otherwise it
records a blocker and emits the backfill command. The lower-level phase receipt verifier remains
available with `npm run sfn -- run verify --receipt loop-run.json`. No phase advances without its
required receipts; the verify/proof milestone cannot complete without a passing `proof-verdict.json`.
Doctrine: [`references/ralph-loop-ledger.md`](references/ralph-loop-ledger.md); copyable
implementation: [`templates/loop/`](templates/loop/).

**Nested phase RALPH:** the macro RALPH ledger is not enough. Each major phase also has its own
`R/A/L/P/H` gates via `npm run sfn -- phase verify --phase <discover|benchmark|setup|build|adapter|verify|iterate>`.
`verify` must emit the failure route, and `iterate` must consume that verified evidence to route back
to the earliest broken phase. Do not patch from vibes; no Phase 6 proof means no Phase 7 fix.

## Research spine (required for research-backed implementation)

The agent must not turn a founder's domain prompt into unsupported architecture or product claims. At
`discover`, create or refresh a `research-spine.json` with user needs, inspirational references,
current research, implementation decisions, eval metrics, and required proof artifacts. From `build`
onward, fail closed if a major implementation decision lacks a decision receipt citing at least one
research source, one practical/reference source when available, and one eval metric. From `verify`
onward, fail closed if a major capability/result claim lacks proof artifacts. Unsupported stretch lanes
must be labeled `unsupported_assumption` or `rejected`, never sold as shipped capability. Doctrine:
[`references/research-spine.md`](references/research-spine.md); copyable implementation:
[`templates/research/`](templates/research/).

**3D founder scenario:** for picture/text/video/reference-media-to-3D requests, default to a
first-party plan: reference-media intake + rights/provenance gate -> first-principles component
breakdown -> capture/coverage -> multi-view reconstruction or local/open image/text-to-asset -> depth
fallback -> assetize/export -> Three.js/WebGL viewer action protocol. Meshy/Tripo/Rodin/Luma are
comparator or fallback lanes, not the product architecture unless the founder explicitly chooses
provider-first. Exact extraction of protected movie/game/social/textbook assets without rights proof
is blocked. Educational purpose is recorded as context, not treated as automatic permission. Allowed
modes are user-owned or licensed media, public-domain/compatible-license media, real-world factual
object reference, or transformed inspiration with similarity/provenance receipts. Before generation,
produce a component tree, functional geometry/material map, protected-expression filter, and
originality delta so the output is an original design from abstracted components. Use
`npm run sfn -- 3d plan ...` and `npm run sfn -- 3d verify ...`.

**Engineering invention harness:** for engineer/inventor requests that mention urgent, safety-critical,
life-support, medical, field-repair, or "life and death" stakes, use `npm run sfn -- engineering plan
...` before build work. The harness may allow an exact previous model only inside a sealed,
non-exportable study sandbox for measurement and first-principles extraction. The final generator must
receive only the filtered functional spec, never the raw replica. Urgency accelerates triage,
simulation/test planning, and receipt collection; it does not permit exact replica export, human use,
or customer/regulator claims without hazard analysis, simulation or bench-test evidence, qualified
human engineering approval, and an export-eligibility verdict. Medical or life-support lanes also
require regulatory-scope review.

**Fresh-user and proof gates:** screenshot-only founder requests must be proven through a fresh
nontechnical emulation receipt (`npm run sfn -- fresh-user ...`) and a full proof pack
(`npm run sfn -- proof full-verify ...`). A plain recording is not enough: require full-screen video,
separate recording audit, terminal transcript, Playwright trace/video, deployed URL, generated assets,
export/reopen proof, scorecard, cost/latency, and a trust-root verdict. Use
`npm run sfn -- trust verify ...` to prove held-out salt, scorer, and final verdict stay outside the
agent process.

## Agent-ready API gate (hard for tools)

Every production tool exposed to a model must be agent-ready by construction. Backend validation is
not enough; the provider-facing schema and description are what the model sees. During **build** and
**adapter**, produce an `agent-api-contract.md` or JSON equivalent for every production tool and
verify it with `npm run sfn -- agent-api verify --contract <file>`. The contract must include:
tool purpose, input/output schema, provider schema parity, required args, semantic lifecycle
(`search -> resolve -> preview -> execute -> verify -> recover`), when to use, when not to use,
preconditions, success signals, structured failure modes, recovery paths, cost/latency class,
permission level, mutation flag, approval requirement, and examples. Doctrine:
[`references/agent-ready-api.md`](references/agent-ready-api.md); copyable verifier:
[`templates/agentApi/`](templates/agentApi/).

## gstack operating lanes (portable operating review team)

Use `garrytan/gstack` as an operating-method inspiration, not a Claude Code lock-in. Before accepting
high-impact work, select the specialist review lanes with `npm run sfn -- gstack recommend ...`
([`templates/gstack/gstackBridge.ts`](templates/gstack/gstackBridge.ts)). The bridge maps gstack-style
CEO/product, engineering, design, developer experience, staff review, QA, security, release, guardrail,
docs, and retro roles onto this loop and requires receipts before claims can pass. Examples:
`discover` needs office-hours + CEO review; UI `build` needs engineering + design review before
implementation and staff review before landing; security-boundary work needs a CSO threat receipt;
deployed `verify` needs live QA, release/deploy, and canary receipts. Doctrine:
[`references/gstack-bridge.md`](references/gstack-bridge.md); copyable implementation:
[`templates/gstack/`](templates/gstack/).

## The loop - run in order; read the playbook for each phase

| # | Phase | Goal | Weight | Gate | Playbook |
|---|---|---|---|---|---|
| 1 | discover | deep-read the app + web-search -> capability spec | light | no | `nodes/1-discover.md` |
| 2 | benchmark | pick the benchmark matching the deliverable shape + author the rubric | light | no | `nodes/2-benchmark.md` |
| 3 | setup | stand up the eval env (Docker/Harbor/HF/verifier) | heavy | yes | `nodes/3-setup.md` |
| 4 | build | build the missing agent + UI/UX pieces (calls the **Design Bridge** subroutine for the UI) | per-stack | yes | `nodes/4-build.md` |
| 5 | adapter | wire the app real agent into the harness (no answer-keys) | medium | yes | `nodes/5-adapter.md` |
| 6 | verify | run the same task in the live app UI; browser-confirm transfer (**Design Bridge** verifies the rendered surface) | medium | no | `nodes/6-verify.md` |
| 7 | iterate | route proof failures back to discover / benchmark / setup / build / adapter, apply one research-backed fix, and re-run verification | medium | cost | `nodes/7-iterate.md` |

Discover + benchmark define *what good is*; setup + build + adapter make it runnable; verify proves
what happened in the live UI; iterate decides which earlier phase must change and repeats the proof.
Phases 6-7 are the loop you repeat, in that order: proof first, fix second.

When running the harness directly, see [`templates/run/README.md`](templates/run/README.md). Its
top-of-file mode-selection table prevents the most common misreport: quoting api-mode scores as your
agent's performance.

## Design Bridge (subroutine - invoked by build + verify)

Not a phase. A subroutine **build** (phase 4) and **verify** (phase 6) call when a UI gap is
architectural/visual and a design tool (Figma MCP, Codex "Implement designs") is connected. **Order is
the guardrail:** structured Design Brief FIRST (user job, missing surface, required components, design
tokens, layout/motion/a11y constraints, current-UI screenshots, the exact code surfaces to change) ->
design output SECOND (inspect/generate via the design MCP) -> produce a Component Contract ->
implement THIRD by REUSING existing components (no one-off CSS drift) -> browser-verify LAST
(Playwright screenshot, DOM signal, visual diff, interaction path, mobile breakpoint, token usage).
**Cost gate:** guide -> generate -> gate before burning design calls or writing back to canvas (same
discipline as the setup install gate). A design MCP is an artifact generator + validator, **not**
product truth. Avoid "make it pretty" / "redesign the whole app" / one giant Figma prompt; prefer
compact, contract-driven prompts on existing tokens. Spec:
[`references/design-bridge.md`](references/design-bridge.md); copyable templates in
[`templates/design/`](templates/design/) (design-brief, component-contract, visual-regression-checklist).

**Design skills are portable inputs, not Claude Code lock-in.** Before calling any design MCP or
writing UI code, select the relevant design guidance with `npm run sfn -- design recommend ...` for a
short plan or `npm run sfn -- design flow ...` for the full transcript flow
([`templates/design/designSkillBridge.ts`](templates/design/designSkillBridge.ts)). Claude-origin
frontend skills, shadcn skills, GSAP skills, UI UX Pro Max, Expo, Material 3, and design registries
are consumed as markdown/tooling references that Codex, Claude Code, Cursor, Windsurf, Copilot, or a
generic coding agent can apply. Do not require a Claude-only slash command or plugin to implement the
surface; port the design decisions into the Design Brief and Component Contract.

The full flow must classify the surface before code: marketing/portfolio uses break-default direction;
functional products use component systems + industry-fit design intelligence; dashboards require
information architecture; mobile is not small web. Select exactly the needed lanes: one style preset
when useful (`minimalist`, `industrial-brutalist`, `all-rounder`, or `premium`), `--visuals` only when
generated image/video assets are part of the product, and `--platform ios|android|cross-platform`
only when the surface is actually mobile/native. Generated media, shadcn MCP registry pulls, and
native mobile guidance still require browser/device proof.

**Design quality gate (hard for UI).** A UI-facing task must run the Design Bridge automatically. The
design tool is optional; the **design quality gate is mandatory**. The goal is to enforce the **best
UI/UX** the task can support, not merely a mechanically working internal harness. A UI-facing build
cannot pass verify until it has a `design-quality-receipt` from `npm run sfn -- design gate ...`
([`templates/design/designQualityGate.ts`](templates/design/designQualityGate.ts)). The receipt must
show: surface classification, distinctive direction, industry fit, component-system choice, state
matrix, responsive proof, desktop + mobile browser screenshots, real interaction proof, accessibility
check, and anti-generic review. Functional product UIs must select product UX/industry-fit guidance
and a component-system lane; 3D apps must prove a full-bleed viewer/workspace-console primary surface,
not a tiny framed preview card. If the visual verdict is `internal-harness`, `needs-redesign`, or
`not-run`, the UI claim is blocked even when the agent mechanics work.

## Memory substrate (local-first, audit-safe)

Each phase **reads safe project memory at start** (decisions, approvals, benchmark choice, setup env,
design constraints, prior rejected fixes) and **writes decision/provenance memory at end** so a founder
resuming next day re-hydrates instead of re-deriving. What each phase reads/writes: discover ->
capability spec + open questions; benchmark -> rubric + the **frozen** split policy/hashes; setup ->
env provenance (image digest, dataset revision, disk paths, smoke baseline); build -> template choice
+ wired seam + TODO stubs; adapter -> adapter path + routed model_id + the honest-baseline writer
mode; verify -> the DOM signal, screenshot path, run id, transfer ledger, generated/exported artifacts,
proof verdict, and failure classes; iterate -> the routed phase to revisit, the research-backed fix,
the rework entry, the held-out/generalization **deltas**, and kill-threshold progress.

**FOUR LEVELS:** L0 phase-scratch (discarded after the phase); L1 project (spec, benchmark choice,
stack facts, approved decisions, commands, design constraints, runner paths); L2 evaluation (split
**hashes**, split policy, run ids, scorecards, failure clusters, fixes, provenance); L3 founder
preference (stack, disk paths, design style, approval rules, budget/model prefs - cross-project).

**CRITICAL QUARANTINE:** held-out / off-distribution task **CONTENTS must NEVER enter persistent
memory**; store only split hashes, aggregate scores, and failure classes. This is the memory-side
mirror of NO ANSWER-KEYS: it stops memory from becoming an answer-key leak path across sessions. Each
event carries a benchmark-safety level (`safe | tuned_only | aggregate_only | heldout_forbidden` ->
REJECT the write | `redacted` -> local only). **One sentence:** remember decisions, constraints,
proofs, and preferences - not benchmark answers.

**SAFE STACK (local-first):** SQLite/libSQL = source of truth; FTS5 = default keyword-recall path;
optional embeddings + RRF + rerank + low-confidence rejection (do NOT hallucinate memory); JSONL =
append-only audit ledger; OKF = portable Markdown+YAML export. Mem0 is an OPTIONAL adapter for safe
cross-project preference memory ONLY (filter its sync to exclude held-out content, PII, keys) - never
the authority. Doctrine + the `SoloMemoryEvent` contract + the memory tools the skill calls:
[`references/memory.md`](references/memory.md); copyable templates in
[`templates/memory/`](templates/memory/) (types.ts, schema.ts, localMemory.ts, retrieval.ts,
okfExport.ts, mem0Adapter.ts, solo-memory.schema.json, memory-policy.md). The LIVE implementation
belongs in the founder's own app (e.g. `src/nodeagent/memory/`) - reference it, do not inline it here.

## Build to delete (hard for rework)

Disposable scaffolding is allowed; undocumented replacement is not. When a path is deleted,
deprecated, or replaced because proof showed it failed, record a rework ledger entry with the old
approach, why it seemed right, what failed, the failure receipt, the new approach, why it survived,
the proof receipts, what was deleted, what survived, and the lesson. Verify with
`npm run sfn -- rework verify --ledger rework-ledger.json`. Doctrine:
[`references/build-to-delete.md`](references/build-to-delete.md); copyable verifier:
[`templates/rework/`](templates/rework/).

## Output

A **scorecard** - tuned / held-out / generalization, each with its honesty state - plus the
**in-app transfer proof** (browser evidence) and a one-line verdict: **real capability or overfitting.**

Reuse: a deterministic, no-LLM grader and a worked example live at `docs/eval/nonbtb/` and
`docs/eval/BTB_GENERALIZATION_DIAGNOSTIC.md` (repo root; distilled from NodeRoom, the origin).

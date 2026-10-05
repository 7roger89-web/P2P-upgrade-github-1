<!--
P2P_PORTABLE_LAW_PROJECTION=YES
SCHEMA=p2p-portable-law-projection/1
CANONICAL_SOURCE=7roger89-web/P2P-upgrade-github-1@main:docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md
SOURCE_CONTENT_SHA256=316936bc951a466c89cc8efb9291f9425571cf886199c8f4f4372be5d7c25ae4
PORTABLE_EXPERIENCE_CONTENT_SHA256=9b10fafe780e47bc82da89d6893d1a88a32c06031dfd7cfb63effc89926cce82
PORTABLE_SKILL_MANIFEST_SHA256=17ad709a095c6cd9c0962606f30ec440718dde7fde6168713d7401a227db2639
PACKAGE_VERSION=8.4.7-C-codex.74
PROJECTION_DO_NOT_EDIT=YES
CANONICAL_WINS_WHEN_REACHABLE=YES
-->

# P2P_OPERATIONS_NOTEBOOK

Status: `CANONICAL_IN_DEVELOPMENT_SOURCE` (candidate, `UNPROMOTED`)
`CANONICAL_PROMOTED: NO`

This is the **single canonical operations notebook** for how a human
beginner, Control Tower, Arena Writer, Arena Supervisor, Codex, Manus, or
another supported executor operates a P2P-installed project. It is the
durable operating memory for P2P operations.

This document is documentation/operations-memory only. It does not grant
permissions, certify a live provider, approve a release, or replace Task
State, the execution ledger, evidence authority, the sole P2P router, or any
existing governance surface.

## 1. Canonical status and authority shape

There is exactly one canonical logical artifact: `P2P_OPERATIONS_NOTEBOOK`.
No parallel operations notebook, manual, or handoff framework may be created
alongside it. When another artifact needs operating rules, it references this
notebook or the existing surfaces below; it does not maintain a divergent
copy.

```text
P2P_OPERATIONS_NOTEBOOK (this file)
        |
        +--> Control Tower operating guidance
        |      docs/p2p-development/CONTROL-TOWER-SESSION-HANDOFF.md
        |
        +--> Arena Writer/Supervisor operation
        |      docs/ARENA_AGENT_MODE_PROTOCOL.md
        |
        +--> installed-project entrypoint
               target project AGENTS.md P2P block, projected by installers
               from the thin source docs/p2p-development/P2P-AGENTS-INSTALL.md
```

The Arena-specific session contract lives in
`docs/ARENA_AGENT_MODE_PROTOCOL.md`; the Control Tower return/rotation
contract lives in `docs/p2p-development/CONTROL-TOWER-SESSION-HANDOFF.md`;
the installed-project entrypoint lives in the `AGENTS.md` P2P block (thin
content sourced from `docs/p2p-development/P2P-AGENTS-INSTALL.md`, not a
copy of this notebook). This notebook is the operations memory above them;
it does not duplicate their contracts.

## 2. Install inheritance law

```text
P2P_INSTALL => P2P_OPERATIONS_NOTEBOOK_ACTIVE_BY_DEFAULT
```

Every project receiving a normal P2P installation must receive/discover
these operating rules automatically. Local installed projections and
Git-tracked portable projections serve different transport cases:

- `install.sh` / `install.ps1` read the thin package file
  `docs/p2p-development/P2P-AGENTS-INSTALL.md` and project that content into
  the target project's `AGENTS.md` as the
  `<!-- BEGIN P2P CODEX --> ... <!-- END P2P CODEX -->` entrypoint block
  (`P2P-PROJECT-BOOTSTRAP.md` documents this entry contract). The thin
  entrypoint preserves progressive disclosure: it names this notebook and the
  P2P_SUPREME_OPERATING_LAW_V1 / P2P_BEGINNER_OPERATIONS_UX_V1 / RULE_ASSIMILATION_GATE_V1 rule sets and points
  execution at the canonical/installed notebook instead of copying the full
  rule bodies, so every installed project discovers them.
- The installed full notebook is projected locally at
  `.p2p/system/docs/P2P-OPERATIONS-NOTEBOOK.md` for executors operating in the
  installed project environment.
- `scripts/p2p_portable_law_projection.py` creates the Git-trackable
  `.p2p/portable/P2P-OPERATIONS-NOTEBOOK.md` plus a small managed `AGENTS.md`
  entrypoint for a P2P-managed repository that may be cloned by a remote
  executor without cross-repository access to the private P2P source. This is
  a generated transport projection, not a second law authority. For such
  remote-clone projects, project provisioning must generate and commit these
  two artifacts before substantive remote executor work.
- Release packages ship BOTH the full notebook
  (`docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md`) and the thin installed
  entrypoint source (`docs/p2p-development/P2P-AGENTS-INSTALL.md`) through
  `scripts/package_release.py` (`DOC_FILES`), and the portable projector via
  `SCRIPT_FILES`, so the same sources can provision later projects without a
  manual copy step.
- Example projects (APP GAME TRUYỆN, LOGISTICS, GIA PHẢ, future projects)
  are examples only. Nothing in this notebook or any runtime hard-codes
  them.

Do not maintain hand-edited per-project copies of the law. Regenerate a
portable projection from the current P2P source/release package. If an
installed entrypoint or generated projection and this reachable canonical notebook
ever differ, the reachable canonical notebook wins.

## 2A. P2P_SUPREME_OPERATING_LAW_V1

This section is the highest active P2P operating law for task execution,
prompt writing, Control Tower routing, and executor preparation. Lower P2P
operating rules remain active only where they do not conflict with this law.
Do not create a parallel supreme-law file or duplicate framework.

### Mandatory preflight

```text
P2P_MANAGED_PROJECT_OR_TASK_START => READ_P2P_SUPREME_OPERATING_LAW_V1
ANY_SUBSTANTIVE_ANALYSIS_OR_REASONING => READ_P2P_SUPREME_OPERATING_LAW_V1_FIRST
CONTROL_TOWER_BEFORE_PROMPT_WRITE => READ_P2P_SUPREME_OPERATING_LAW_V1
P2P_PROMPT_WRITER_BEFORE_PROMPT_WRITE => READ_P2P_SUPREME_OPERATING_LAW_V1
EXECUTOR_BEFORE_IMPLEMENTATION => READ_P2P_SUPREME_OPERATING_LAW_V1
REVIEWER_OR_SUPERVISOR_BEFORE_REVIEW => READ_P2P_SUPREME_OPERATING_LAW_V1
MODEL_SWITCH_OR_SESSION_RESET => READ_P2P_SUPREME_OPERATING_LAW_V1_AGAIN
NO_SUBSTANTIVE_WORK_BEFORE_VALID_LAW_CONTEXT = YES
ACTOR_OWN_LAW_READ_RECEIPT_MANDATORY = YES
PARENT_SELF_LAW_PREFLIGHT != EXECUTOR_LAW_PREFLIGHT
CONTROL_TOWER_SELF_LAW_RECEIPT != EXECUTOR_LAW_RECEIPT
WRITER_RECEIPT != SUPERVISOR_RECEIPT
```

This preflight applies to every P2P-managed project and every P2P-managed
Control Tower, prompt writer, executor, reviewer, supervisor, model, or
supported tool session. Before substantive operational analysis, decision
reasoning, planning, prompt construction, implementation, review, testing, or
release work, the actor must first establish a valid Supreme Law context.
This requirement concerns the operating law used to make decisions; it does
not require disclosure, storage, or narration of private chain-of-thought.

Every actor (Control Tower, prompt writer, executor, reviewer, supervisor, tool
session) must establish and visibly expose its OWN Supreme Law read receipt before
its first substantive work unit or operational response:

```text
LAW_CHECK=PASS | SOURCE=<actual source> | SOURCE_SHA256=<canonical source content sha256>
```
or:
```text
LAW_CHECK=BLOCKED | REASON=<reason>
```

Rules for the actor self-read receipt:
- Only an actually performed read counts. Inferring, guessing, copying, or
  assuming a read from chat memory is forbidden.
- `PARENT_SELF_LAW_PREFLIGHT != EXECUTOR_LAW_PREFLIGHT`.
  `CONTROL_TOWER_SELF_LAW_RECEIPT != EXECUTOR_LAW_RECEIPT`.
  `WRITER_RECEIPT != SUPERVISOR_RECEIPT`.
  One actor cannot copy or inherit another actor's receipt.
- Law source precedence remains strict: reachable canonical > installed
  projection > fresh portable projection > inline capsule.
- A portable projection receipt (`LOCAL_PORTABLE`) can yield `LAW_CHECK=PASS` only
  when bound to the recorded `SOURCE_CONTENT_SHA256` matching the canonical
  notebook content SHA-256. A stale portable copy cannot produce `PASS`.
- `LAW_CHECK=BLOCKED` requires immediate cessation of substantive work.
- The receipt is verifiable preflight evidence only; it grants no execution
  authority, permission widening, or acceptance waiver.
- `LAW_READ_RECEIPT != LAW_APPLICATION_EVIDENCE`. A truthful
  `LAW_CHECK=PASS` proves only that the actor established source-bound law
  context; it does not prove that later material decisions actually applied
  the relevant law.
- When a material decision is changed, constrained, blocked, or simplified by
  a Supreme Law clause, bind that observable consequence to the existing
  evidence/status/ReturnPacket/task-state surface where it materially helps
  verification. Do not add per-turn ceremony, private-chain-of-thought
  narration, or a second law-compliance ledger.

A valid law context is, in precedence order: the reachable active canonical
notebook; an up-to-date installed projection of that notebook; an up-to-date
generated portable project projection; or, when those sources cannot be
reached, the explicit compact `SUPREME_LAW_CAPSULE` carried by the P2P prompt.
A stale task branch, old chat, old plan, remembered summary, hand-edited copy,
or executor-specific convention is not a valid replacement for the active
law. If none of the valid law contexts is available, substantive P2P-managed
work must stop at `LAW_CONTEXT_BLOCKED` until a valid context is supplied.

The canonical text is this section of
`7roger89-web/P2P-upgrade-github-1@main:docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md`.

`TASK_BRANCH != LAW_AUTHORITY`.
`TARGET_PROJECT != LAW_SOURCE`.

The target repository, worktree, and task branch are execution state only and
must not select the Supreme Law version. In an installed project,
`.p2p/system/docs/P2P-OPERATIONS-NOTEBOOK.md` is a valid local projection only
when it contains `P2P_SUPREME_OPERATING_LAW_V1`. In a P2P-provisioned remote
project, `.p2p/portable/P2P-OPERATIONS-NOTEBOOK.md` is a valid transport
projection only when it is generated by the P2P portable projector, contains
`P2P_PORTABLE_LAW_PROJECTION=YES`, identifies the canonical source and source
content SHA-256, contains `P2P_SUPREME_OPERATING_LAW_V1`, and is not known to
be stale or modified. Neither local projection outranks a reachable active
canonical source.

When canonical cross-repository access is unavailable, the executor should use
a valid generated portable projection first when one is present. If neither
canonical nor a valid local projection can be read, the P2P-generated prompt
must carry the compact `SUPREME_LAW_CAPSULE` inline. The executor must report
which law source it actually read and must not claim that it read a repository
file it could not access. The prompt writer must not copy the whole notebook
into ordinary prompts when the generated projection or compact capsule is
sufficient.

### Remote repo-scoped projection freshness gate

A handoff to a remote executor that may only see the target repository must
not rely on a portable projection merely because the file exists.

```text
REMOTE_REPO_SCOPED_HANDOFF => FRESH_CHECK_TARGET_PORTABLE
KNOWN_STALE_OR_MISSING_PORTABLE != VALID_LAW_CONTEXT
```

When the parent Control Tower or prompt writer has authenticated access to the
canonical P2P source and the Git-hosted target repository, it must perform the
smallest freshness check before delegating substantive work:

1. fresh-read the active canonical notebook and establish its content SHA-256;
2. read the target repository's `AGENTS.md` and portable projection header;
3. if the portable projection is missing or its recorded source identity does
   not match the fresh canonical source, refresh the target projection using
   the existing projector semantics: full canonical notebook plus provenance
   header and the managed `AGENTS.md` portable-law block;
4. verify the target repository state now carries the matching source identity
   before telling a repo-scoped executor to rely on `LOCAL_PORTABLE`.

For GitHub-hosted projects, an already-authorized GitHub connector/repository
write path may perform this refresh on a branch/PR without requiring a local
clone. Use existing merge/Owner-Gate rules; this gate grants no new merge,
deployment, secret, infrastructure, or destructive authority.

If the parent can read canonical law but cannot safely refresh the target
repository, it must mark the target portable projection stale/missing and
serialize a fresh compact `SUPREME_LAW_CAPSULE` for that handoff. The
repo-scoped executor must then report `P2P_LAW_SOURCE=INLINE_CAPSULE`; it must
not treat a known-stale portable file as current law.

Before delegating substantive work to a remote executor, the parent Control
Tower or prompt writer must make target-law freshness visible with a compact
receipt:

```text
TARGET_LAW_FRESHNESS=CURRENT | REFRESHED | INLINE | BLOCKED
CANONICAL_LAW_SHA256=<canonical content sha256>
TARGET_LAW_SHA256=<target projection content sha256>
```

Interpretation:
- `CURRENT` — target repository portable projection matches active canonical source SHA-256.
- `REFRESHED` — stale or missing target projection was refreshed to match canonical and verified before handoff.
- `INLINE` — safe target refresh unavailable; fresh inline `SUPREME_LAW_CAPSULE` supplied for executor preflight.
- `BLOCKED` — no valid law context route is available; delegation is blocked.

This is a handoff-time freshness gate, not a background synchronization
service. Do not add a daemon, watcher, polling loop, repository registry,
GitHub Action, PAT/secret, or second control plane solely to keep projections
fresh.

### Bounded ACTIVE experience preflight invariant

```text
NON_TRIVIAL_TASK_START => BOUNDED_ACTIVE_EXPERIENCE_LOOKUP
EXPERIENCE_CHECK=USE_ACTIVE_EXPERIENCE | NO_MATCH | UNAVAILABLE
```

For every non-trivial P2P-managed task, execution order is mandatory:

```text
LAW/TASK PREFLIGHT -> BOUNDED EXPERIENCE LOOKUP -> SUBSTANTIVE EXECUTION
```

Before substantive execution, every executing actor must perform a bounded lookup
of promoted ACTIVE experience and emit an observable receipt:

```text
EXPERIENCE_CHECK=USE_ACTIVE_EXPERIENCE | IDS=<experience_id,...>
```
or:
```text
EXPERIENCE_CHECK=NO_MATCH
```
or:
```text
EXPERIENCE_CHECK=UNAVAILABLE
```

Retrieval paths:
- Installed-runtime path: run `python .p2p/system/p2p_capabilities/experience_evolution.py --root . retrieve --task-text "<task>"`.
- Remote repo-scoped path: read `.p2p/portable/P2P-EXPERIENCE-CAPSULE.json` directly and match trigger tokens against promoted ACTIVE records.
- Control Tower path: use `activation_summary` and bounded prompt context injection.

Invariants:
- Maximum returned active experiences remains small (default <= 3).
- Experience is `NON_AUTHORITATIVE_VERIFIED_EXPERIENCE`: it is advisory context only.
- Current Supreme Law, active task contract, fresh repository/project truth, and current provider/tool evidence always outrank prior experience.
- Experience cannot widen permissions, change acceptance authority, or silently rewrite Supreme Law or skills.

### Task-end learning reconciliation invariant

```text
TASK_RECONCILIATION => LEARNING_RECONCILIATION
ROUTINE_SUCCESS => LEARNING_RECONCILIATION=NONE
REPEATED_OR_MATERIAL_FAILURE | CLEARLY_REUSABLE_CORRECTION => LEARNING_RECONCILIATION=CANDIDATE
```

At task completion and reconciliation, the actor and Control Tower must close
the learning loop:
- `ROUTINE_SUCCESS` => emit `LEARNING_RECONCILIATION=NONE`. Do not manufacture
  memory or candidates from routine success.
- `REPEATED_OR_MATERIAL_FAILURE` or `CLEARLY_REUSABLE_CORRECTION` => emit
  `LEARNING_RECONCILIATION=CANDIDATE` (or the appropriate lifecycle state). Terminal
  task closure is invalid unless either:
  1. an experience candidate is created with concrete evidence and trigger conditions; or
  2. an explicit, evidence-based reason is recorded why no reusable lesson exists.
- Memory must never be created from model self-report, chat summaries, or private
  thoughts alone.
- Preserved lifecycle: `CANDIDATE -> VERIFIED -> ACTIVE -> SUPERSEDED | QUARANTINED`.
- Multi-project scope classification: `PROJECT_ONLY | DOMAIN | CROSS_PROJECT`.
- No executor self-promotion into Supreme Law, shared authority, capability, or skill.

### GitHub connector preflight and failure classification

GitHub-dependent work must distinguish the Owner's ChatGPT GitHub connection
from the capabilities of one executor, sandbox, chat, model, or product
surface. A single failed tool call or an executor that lacks GitHub access is
not evidence that the Owner's connector is disabled.

```text
EXECUTOR_GITHUB_ACCESS != OWNER_GITHUB_CONNECTOR_STATUS
ONE_FAILED_CALL != GITHUB_CONNECTOR_DISABLED
SESSION_TOOL_UNAVAILABLE != ACCOUNT_CONNECTION_BROKEN
```

Before a Control Tower concludes that GitHub access is unavailable for a
P2P-managed task that materially depends on GitHub, use the smallest direct
preflight available on the current authoritative ChatGPT/connector surface:

1. confirm an authenticated GitHub identity/installation when that surface is
   available;
2. read the target repository or another known private repository covered by
   the installation; and
3. read one known branch/ref/file when the task depends on repository content.

Classify the result instead of collapsing every failure into `disabled`:

```text
GITHUB_CONNECTOR_STATUS=WORKING
GITHUB_CONNECTOR_STATUS=SESSION_SURFACE_UNAVAILABLE
GITHUB_CONNECTOR_STATUS=REPO_SCOPE_BROKEN
GITHUB_CONNECTOR_STATUS=AUTH_CONNECTION_BROKEN
GITHUB_CONNECTOR_STATUS=PROVIDER_OUTAGE
```

Interpretation and recovery:

- `WORKING` — direct authenticated repository access succeeds; continue.
- `SESSION_SURFACE_UNAVAILABLE` — the current executor/chat/model/sandbox lacks
  the tool or cannot use it, while the Owner connection is not proven broken.
  Do not disconnect, reinstall, or rewrite credentials. Use another supported
  surface/fresh session when needed, or continue from durable GitHub state by
  another authorized route.
- `REPO_SCOPE_BROKEN` — authentication works but the required repository is not
  accessible. Check the GitHub App installation/repository selection before
  changing unrelated network or project settings.
- `AUTH_CONNECTION_BROKEN` — authenticated identity/installation cannot be
  established on a supported direct connector surface. Only this class (or
  equivalent direct evidence) justifies reconnecting/re-authorizing the Owner
  connection.
- `PROVIDER_OUTAGE` — fresh direct checks fail consistently and provider-status
  evidence or equivalent cross-session evidence indicates a service incident.
  Preserve credentials/configuration and avoid speculative reconnect loops.

An executor may truthfully report
`EXECUTOR_GITHUB_ACCESS=UNAVAILABLE_IN_THIS_SESSION`, but it must not promote
that local observation to `OWNER_GITHUB_CONNECTOR=DISABLED` without the direct
preflight above. Control Tower owns the cross-surface classification and must
prefer fresh connector evidence over an executor's local capability claim.

Do not create a connector-health daemon, polling service, registry, or
monitoring framework for this rule. Run the preflight only when GitHub access
is materially required or when a relevant failure is observed, then stop once
the failure class is established.

### Supreme laws

1. **OWNER_OUTCOME_AND_AUTHORITY_ARE_INVARIANTS** — Understand the outcome and
   acceptance that matter to the Owner. The agent decides routine technical
   details inside approved scope. Ask the Owner only for genuine outcome,
   authority, material cost, security/privacy/business-impact, production,
   destructive, infrastructure-commitment, or hard-to-reverse decisions. Never
   lower acceptance or widen authority to manufacture success. A fully
   validated PR merge covered by the standing
   `VALIDATED_PR_AUTO_MERGE_AUTHORITY` (RULE 11) is a routine integration step
   inside approved scope, not an authority decision to re-ask; promotion,
   release, and deployment remain Owner decisions.
2. **SIMPLEST_USEFUL_PATH_TO_COMPLETION** — Choose the next action with the best
   practical contribution to completion at reasonable complexity, cost, and
   risk. A useful action directly advances the outcome, changes a meaningful
   decision, establishes a required execution/recovery condition, produces
   acceptance evidence, or reduces a material risk. Do not open speculative
   architecture or infrastructure before the core capability shows a need.
3. **REAL_STATE_AND_EVIDENCE_OVERRIDE_ASSUMPTIONS** — Fresh-check relevant state
   before mutation when it may have changed. After material actions, verify the
   real result before relying on it. Evidence proves only its own scope. If a
   mutation may have happened but acknowledgement is lost, treat the state as
   `UNKNOWN` and reconcile before an unsafe retry.
4. **RECOVER_ADAPTIVELY; DO_NOT_ENTER_SPECULATIVE_FIX_LOOPS** — Retry policy
   depends on process type: deterministic repair, stochastic sampling,
   transient infrastructure, and unknown-side-effect recovery are not the same.
   Do not use a fixed failure count as a hard stop. Do not convert every isolated
   failure into a permanent rule or new infrastructure. For a repeated or
   materially consequential failure, identify the failure class/root cause and
   apply the lightest durable fix that prevents recurrence at acceptable cost.
   A branch is stuck when cost/scope/complexity keep increasing without
   preserved progress toward acceptance or decision-useful evidence. Stop
   speculative mutation, preserve evidence, re-diagnose, change
   route/model/harness when justified, or return `BLOCKED` with an
   `INFEASIBLE` verdict/reason when current constraints make the outcome impossible.
5. **PRESERVE_CONTINUITY_AND_STOP** — For long work, retain only the durable
   checkpoint needed to continue: active goal/boundaries, current
   version/state, verified progress/evidence, decisions or blockers that still
   matter, and the next useful action. Decompose only when it improves
   execution, verification, recovery, or context. When the required outcome is
   proven, stop instead of opening optional refactor, benchmark, framework,
   hardening, or future-phase work.
6. **PROMPT_TITLE_DESTINATION_AND_PLAN_STATE_ARE_EXPLICIT** — Every P2P-generated
   operational prompt handed to the beginner Owner for execution in another
   tool/chat must state the target project/workstream, destination/tool,
   `CHAT_MODE=NEW_CHAT` or `CHAT_MODE=SAME_CHAT`, the exact existing chat name
   when continuing (or a recognizable `CHAT_TITLE` when new), and the role where
   applicable. For Arena, and for any destination where a new conversation title
   is derived from the opening prompt text, `NEW_CHAT` prompts must follow
   `ARENA_CHAT_TITLE_FIRST_LINE_V1`: the **first nonblank line** is one concise,
   human-readable task title, normally `<PROJECT> — <bounded task/outcome>`.
   Front-load the distinguishing words so the title remains useful when the UI
   truncates it. That first line must not be routing boilerplate such as
   `GỬI CHO:`, `DESTINATION=`, `TASK_ID=`, a code fence, or a generic `P2P`
   prefix. Immediately after the title, serialize the normal routing metadata,
   including `GỬI CHO: <destination>` (or the destination's equivalent),
   `PROJECT=`, `CHAT_MODE=`, and for `NEW_CHAT`,
   `CHAT_TITLE=<exact same human-readable title>`. For `SAME_CHAT`, the exact
   existing `CHAT_TITLE` remains authoritative and must not be silently renamed.
   The same prompt must include a compact fresh project-plan checkpoint anchored
   to durable state: `PLAN_REFERENCE` (or `NO_FORMAL_PLAN`), what is already
   completed, the current checkpoint, blocker/Owner Gate if any, and the single
   next bounded step. Control Tower refreshes this from the active project
   plan/task state before issuing the prompt; chat memory may supplement but
   never override durable state. The beginner must never infer where to paste a
   prompt, manually rename a newly created Arena chat merely to make the sidebar
   intelligible, or reconstruct project progress from old chats. Do not invent a
   plan when none exists. This compact handoff checkpoint is not continuous
   progress narration and does not override
   `PROGRESS_REPORTING=EXCEPTIONS_ONLY`.

   ```text
   ARENA_CHAT_TITLE_FIRST_LINE_V1=YES
   NEW_CHAT_FIRST_NONBLANK_LINE=<PROJECT> — <bounded task/outcome>
   ROUTING_BOILERPLATE_FIRST_LINE=NO
   NEW_CHAT_CHAT_TITLE_MUST_EQUAL_FIRST_LINE=YES
   ```

7. **ANALYTICAL_AUTONOMY_AND_DELEGATION_ALIGNMENT** — For non-trivial P2P
   reasoning, use analytical scepticism rather than agreement-seeking. Deconstruct
   the Owner goal, acceptance conditions, requirements, assumptions, evidence,
   contradictions, and likely failure modes from the top down, then reconstruct
   the smallest valid solution from the bottom up. Where the distinction matters,
   label or clearly separate verified fact, inference, hypothesis, judgment, and
   recommendation. Prefer root-cause repair over a symptom patch; do not accept a
   compromise merely because it ends disagreement if it fails the actual
   acceptance condition. Generate a small set of commensurate alternatives only
   when they can materially change the decision, and compare them by outcome,
   evidence, risk, reversibility, and complexity rather than by rhetorical
   balance. After a material error, before a critical or hard-to-reverse
   decision, or after repeated analytical cycles without material progress,
   recalibrate the goal model, assumptions, evidence, and method and change
   course when warranted. When material uncertainty could change the decision,
   obtain fresh authoritative grounding or run the smallest representative probe
   that the current permissions/tools allow; do not manufacture pseudo-precise
   confidence thresholds. When claiming a transdisciplinary synthesis, explicitly
   name the disciplines being integrated and the core conflicting concepts being
   reconciled into the new conclusion. Metatheory/metalogic may be used when they
   materially improve diagnosis or synthesis, never as mandatory ceremony.
   Before delegating work to another model, run the prompt-alignment gate below;
   if a capable model following the prompt literally could plausibly drift from
   the Owner's outcome, rewrite the prompt before sending it. Technical analysis
   may operate at expert depth, but Owner-facing explanation must remain
   beginner-clear; Vietnamese is the default Owner-facing language unless the
   Owner requests otherwise or the external artifact/audience requires another
   language. `EXPERT_INTERNAL_DEPTH != EXPERT_OWNER_WORDING`: when a technical
   term is necessary, explain its practical meaning in ordinary Vietnamese on
   first use. A material Owner-facing status update or terminal summary must
   lead with what happened, whether the work is actually done / not done /
   blocked, why that matters, and the single Owner action now; raw technical
   fields may follow as supporting detail. Never make the beginner decode a
   ReturnPacket, SHA, PR status, runtime label, gate name, or other jargon to
   discover the practical outcome. `NOT_RUN != FAIL`,
   `NOT_OBSERVED != NO`, and `BLOCKED_BY_ENVIRONMENT != PRODUCT_DEFECT`;
   unperformed checks must be reported as not verified rather than as observed
   failures. Full beginner-facing wording rules are defined by
   `P2P_BEGINNER_OPERATIONS_UX_V1 > RULE 21 — BEGINNER_PLAIN_LANGUAGE_FIRST`.
   Owner-facing Control Tower communication should be direct, informal,
   adaptive, and willing to criticize weak reasoning without sugar-coating;
   criticism targets the decision/design/work, not the Owner, and never
   overrides safety or audience requirements. The purpose is to increase the
   Owner's intellectual autonomy, not to increase complexity for its own sake.
8. **TASK_CONTRACT_AND_ACCEPTANCE_FIDELITY** — Before delegating or executing a
   non-trivial P2P task, bind the Owner outcome to the smallest useful task
   contract: objective, in-scope and out-of-scope boundaries, real affected
   surface, representative scenario or quality invariant where relevant,
   observable acceptance criteria, required evidence class and proof surface,
   durable artifact identity where applicable, failure/blocker criteria, and
   stop condition. The active contract remains execution authority until an
   explicit Owner/Governance decision or durable successor contract revises it;
   executor findings, local tests, proxy artifacts, screenshots, self-reports,
   or adjacent improvements must not silently rewrite the objective. For
   product, business, visual, UX, educational, legal, data, or workflow work,
   name at least one representative real user/workflow/quality slice when that
   materially defines value; if no such slice can yet be stated, clarify or run
   the smallest representative probe before broad implementation. Evidence must
   be scope-matched: local, static, unit, mock, proxy, preview, synthetic, or
   sandbox evidence proves only that boundary and must not be promoted to a
   live, durable, visual, business, user-facing, official-source, persistence,
   provider, package-transport, or production PASS unless equivalence is
   explicit in the contract and verified by representative proof. A technical
   PASS, CI PASS, local test count, screenshot, or executor self-report is not
   completion when acceptance requires correct branch/base/head or durable PR
   identity, live runtime, visual likeness or interaction quality, real user or
   business workflow fit, source fidelity, persistence, release-package
   transport, provider/host behavior, or Owner-visible acceptance. Reuse-first
   work must prove reuse/composition of the authoritative existing component
   before introducing replacement logic; do not rebuild what the task says to
   assemble unless unusability is established. When repeated repair does not
   materially improve progress toward acceptance, the next attempt must
   diagnose whether the contract, prompt, executor capability, environment,
   evidence class, or acceptance route is wrong; do not issue another
   same-shape repair prompt unless that diagnosis changes or the task narrows
   to a representative proof. A newly discovered concern may block completion,
   but it does not become the new objective unless recorded as an authorized
   contract revision or successor task; useful out-of-scope work is
   `DEFERRED_NOT_REQUIRED`. This rule uses existing P2P task state, evidence,
   handoff, Owner Gate, OE Gate, and routing surfaces and creates no new ledger,
   framework, prompt-linter, CI gate, database, reviewer service, or supervising
   agent.
9. **EXECUTOR_INPUT_FORMAT_AND_ARTIFACT_TRANSPORT_FIDELITY** — A P2P-generated
   prompt must never instruct the beginner Owner (or another executor) to
   provide an artifact through an input path the destination executor cannot
   actually consume. When direct transport is impossible, P2P must choose the
   simplest trustworthy reversible transport and prove that reconstruction
   preserves the original artifact identity. This law is executor-neutral:
   Arena is the current representative case, not the architecture.

   **A. Destination capability before handoff.** Before a P2P-generated
   instruction tells the Owner or another executor to attach, upload, import,
   open, ingest, reconstruct, or otherwise consume an external artifact, the
   prompt writer must establish the actual input capability of the destination
   executor/surface whenever that capability materially affects task
   completion. Canonical principle: `LOCAL_ARTIFACT_EXISTS !=
   DESTINATION_CAN_CONSUME_ARTIFACT`. Never assume that because an artifact
   exists on one machine, chat, workspace, repository, or executor it can be
   directly transported into another. Use fresh authoritative destination
   capability information or the smallest representative probe (RULE 19) when
   material uncertainty remains.

   **B. Direct transport first when actually supported.** If the destination
   supports the artifact's real media/file type through a trustworthy direct
   path, prefer transporting the exact artifact without semantic
   transformation. Possible direct/native paths may include, where actually
   supported and authorized: native attachment, repository file, executor
   workspace, connected storage, or another destination-native lossless
   mechanism. Do not invent extra transport machinery when an existing native
   path is sufficient. When exact artifact identity materially matters, bind
   at minimum `ORIGINAL_FILENAME`, `ORIGINAL_BYTE_SIZE`, and
   `ORIGINAL_SHA256`; record `ORIGINAL_MEDIA_TYPE` when useful for routing or
   validation.

   **C. Unsupported binary format.** If the original binary format is not
   supported directly, do not: rename only the extension; spoof the MIME/media
   type; claim another file type while preserving incompatible bytes; silently
   convert into a semantically different artifact; tell the beginner Owner to
   perform an impossible upload; or treat a transport representation as though
   it were the original artifact. Select the simplest supported, reversible,
   lossless transport available. For Arena, when no simpler destination-native
   lossless route is available and supported text input is feasible, the
   default fallback may be: binary → standard Base64 encoding → supported text
   transport → destination → concatenate if chunked → strict Base64 decode →
   reconstructed binary → byte-size verification → SHA-256 verification →
   artifact may then be used. Canonical invariant: `BASE64_TEXT !=
   ORIGINAL_BINARY`. Base64 is transport encoding only; it is not encryption,
   not secrecy, not an integrity proof by itself, not permission to bypass
   security/privacy/content policy, and not permission to bypass an existing
   Owner Gate. A reconstructed artifact becomes equivalent to the bound
   original only after the required identity checks pass.

   **D. Target isolation.** Temporary transport/reconstruction artifacts must
   be created outside the target project worktree by default. Do not mutate
   the target repository merely to move a file between executors. Canonical
   principle: `EPHEMERAL_TRANSPORT != PROJECT_SOURCE`. Only place
   reconstructed material into the project tree when the actual task contract
   explicitly requires repository mutation. Do not commit temporary Base64
   payloads, chunks, decoded transport scratch files, or transport-only
   material merely for handoff convenience. The default
   `EPHEMERAL_TRANSPORT != PROJECT_SOURCE` prohibition remains absolute; the
   only narrow exception is the proven last-resort fallback defined in §F
   (`LAST_RESORT_SAME_REPO_TRANSPORT_BRANCH`), which still requires
   `TRANSPORT_FILES_EXCLUDED_FROM_ASSESSMENT_TARGET=YES` and
   `TRANSPORT_BRANCH_NEVER_MERGED=YES` and never mutates `main`.

   **E. Size-aware fallback.** Do not assume an undocumented upload-size
   limit. When destination size support materially affects completion, use
   fresh authoritative product state when available or run the smallest
   representative probe; do not invent a numeric size limit. If one supported
   text artifact is accepted, do not chunk it preemptively. If one supported
   text artifact exceeds the destination's real current limit, the simplest
   fallback may be deterministic ordered Base64 text chunks. Bind enough
   information to reconstruct deterministically: `CHUNK_COUNT`,
   `ORDERED_CHUNK_NAMES`, `ORIGINAL_BYTE_SIZE`, `ORIGINAL_SHA256`; use
   per-chunk size/hash where materially useful for detecting transport
   corruption. After ordered concatenation and decoding,
   `FINAL_BYTE_SIZE == ORIGINAL_BYTE_SIZE` and
   `FINAL_SHA256 == ORIGINAL_SHA256` are authoritative for byte identity. If
   they differ, classify `ARTIFACT_IDENTITY_MISMATCH` and the reconstructed
   artifact must not be treated as the original.

   **F. Last-resort same-repository ephemeral transport branch
   (LAST_RESORT_SAME_REPO_TRANSPORT_BRANCH).** This narrow, non-default
   exception is allowed ONLY when ALL are proven empirically — not assumed —
   and no simpler trustworthy native route remains:

   ```text
   DIRECT_ATTACHMENT_ROUTE=UNAVAILABLE_OR_FAILED
   CROSS_REPO_NATIVE_ROUTE=UNAVAILABLE
   DESTINATION_SELECTED_REPO_GITHUB_ACCESS=WORKING
   SUPPORTED_TEXT_TRANSPORT_EXISTS
   NO_SIMPLER_TRUSTWORTHY_NATIVE_ROUTE=YES
   ```

   “Empirically proven” means: a fresh direct attempt for the required
   file type failed or is unsupported under the current capability snapshot
   (§G); cross-repository native access to the private P2P source (or other
   required private repository) returned 404 or equivalent while destination
   selected-repository access succeeded; and no simpler lossless native route
   (native attachment, outside-target-repo destination-native lossless source,
   or directly supported text transport) is reachable. Verify
   `DESTINATION_SELECTED_REPO_GITHUB_ACCESS=WORKING` with a live
   authenticated check — e.g., `GET /installation/repositories` returns only
   the selected target repository and a read of that repository succeeds —
   before using the fallback.

   When the preconditions above hold, the fallback must satisfy ALL of the
   following invariants (fail closed if any is uncertain):

   ```text
   TRANSPORT_BRANCH_IS_EPHEMERAL=YES
   TRANSPORT_BRANCH_NEVER_MERGED=YES
   TRANSPORT_BRANCH_NOT_TARGET_REF=YES

   ASSESSMENT_TARGET= clean detached checkout/worktree at authoritative target main SHA

   TRANSPORT_FILES_EXCLUDED_FROM_ASSESSMENT_TARGET=YES

   ORIGINAL_SIZE_BOUND=YES
   ORIGINAL_SHA256_BOUND=YES
   RECONSTRUCTED_SIZE_VERIFIED=YES
   RECONSTRUCTED_SHA256_VERIFIED=YES

   NO_TARGET_MAIN_MUTATION=YES
   NO_PRODUCT_SOURCE_CHANGE=YES
   NO_PR_REQUIRED=YES

   DELETE_TRANSPORT_BRANCH_AFTER_SUCCESS_OR_TERMINAL_HANDOFF=YES
   ```

   Normative clarifications:

   - The temporary transport branch is repository transport state, NOT project source, NOT a release, NOT a promotion, and MUST NEVER become part of the assessed target tree. `TRANSPORT_BRANCH_IS_EPHEMERAL=YES` is an invariant, not a naming choice.
   - `TRANSPORT_BRANCH_NOT_TARGET_REF=YES` — the transport branch is never the
     assessment target. The scan/validation/OE assessment target is always a
     clean detached checkout/worktree at the authoritative `origin/main` SHA
     (or other authoritative target ref). Transport payloads are never on that
     ref.
   - `TRANSPORT_FILES_EXCLUDED_FROM_ASSESSMENT_TARGET=YES` — Base64 payloads,
     chunks, decoded scratch files, and any transport-only material reside only
     on the ephemeral transport branch and are excluded from the detached
     assessment worktree; only the clean target tree is scanned/assessed.
   - `ORIGINAL_SIZE_BOUND=YES` / `ORIGINAL_SHA256_BOUND=YES` must be bound
     before transport; `RECONSTRUCTED_SIZE_VERIFIED=YES` /
     `RECONSTRUCTED_SHA256_VERIFIED=YES` must be verified after strict decode
     outside the assessment target and before any use; on mismatch classify
     `ARTIFACT_IDENTITY_MISMATCH`.
   - `NO_TARGET_MAIN_MUTATION=YES` and `NO_PRODUCT_SOURCE_CHANGE=YES` — no file
     is committed to `main`, no product source is changed, and no transport
     material is ever merged into any product branch.
   - `NO_PR_REQUIRED=YES` — the ephemeral branch is not opened as a PR and is
     never merged; it is an executor-local transport handle whose sole purpose
     is to make the supported text payload reachable via destination-native
     GitHub access, then reconstruct outside the target and delete.
   - `DELETE_TRANSPORT_BRANCH_AFTER_SUCCESS_OR_TERMINAL_HANDOFF=YES` — delete
     the transport branch immediately after successful reconstruction/use or
     after terminal handoff/BLOCKED, using the same GitHub access that created
     it; do not retain it silently.

   Precedence (normative): the default `EPHEMERAL_TRANSPORT != PROJECT_SOURCE`
   prohibition is preserved and the fallback is never the default. The allowed
   order is:

   ```text
   1. trustworthy direct/native attachment
   2. destination-native lossless source outside target repo when reachable
   3. reversible supported text transport
   4. LAST_RESORT_SAME_REPO_TRANSPORT_BRANCH only after the above are empirically unavailable
   ```

   Do not select (4) without proving (1)-(3) unavailable per §F
   preconditions.

   Prohibitions (normative — even under fallback, never):

   ```text
   transport file on main
   transport file merged into product branch
   transport file included in scan target
   permanent transport directory
   transport service/framework
   silent transport branch retention
   ```

   Violation of any MUST/NEVER clause is an isolation failure, not transport
   convenience. OE gate for this addition: `Không bị over engineering chứ?`
   → `OE_GATE=DO_IT` — one small exception in the existing Rule #9, based on
   repeated empirical transport failure; no transport service, MIME registry,
   artifact server, workflow, daemon, agent, or routing framework is built.

   **G. Current Arena capability snapshot.** Recorded explicitly as bounded
   evidence, not as a second attachment policy system:

   ```text
   CURRENT_ARENA_ATTACHMENT_CAPABILITY_SNAPSHOT
   DATE=2026-09-14
   CLASSIFICATION=CURRENT_EXECUTOR_CAPABILITY_STATE
   NOT_ETERNAL_PRODUCT_GUARANTEE=YES
   OWNER_OBSERVED_ACCEPTED_MEDIA_TYPES:
     image/png, image/webp, image/jpeg, image/gif,
     text/plain, text/markdown, text/csv, text/html, text/xml, text/css,
     text/javascript, application/json, application/xml,
     application/javascript, application/pdf
   ARENA_AGENT_MODE_DOCS_CORROBORATE_UPLOAD_EXTENSIONS:
     PNG, WebP, JPEG, PDF, GIF, TXT, Markdown, CSV, HTML, XML, CSS,
     JavaScript, JSON
   CONCLUSION:
     application/zip = NOT_SUPPORTED_BY_CURRENT_ARENA_DIRECT_ATTACHMENT_INPUT
   ```

   ZIP is therefore not to be prescribed as a direct Arena attachment under
   this current capability state. This is a dated capability snapshot, not an
   eternal product rule. If a later authoritative Arena capability state
   demonstrates that ZIP or another format is supported, then
   `FRESH_DESTINATION_CAPABILITY_STATE > STALE_CAPABILITY_SNAPSHOT`; update
   durable P2P guidance when the changed capability materially affects
   routing, and do not require continued Base64 transport after a simpler
   reliable native transport becomes available.

   **H. Failure classification.** Distinguish executor transport failures from
   artifact/project/provider failures. Transport/input classes:
   `ARTIFACT_UNSUPPORTED_BY_DESTINATION_FORMAT`,
   `ARTIFACT_TRANSPORT_SIZE_BLOCKED`, `ARTIFACT_IDENTITY_MISMATCH`,
   `ARTIFACT_RECONSTRUCTION_FAILED`, `EXECUTOR_INPUT_TRANSPORT_UNAVAILABLE`,
   `EXECUTOR_SINGLE_REPO_SCOPE_TRANSPORT_CONSTRAINT`.
   `EXECUTOR_SINGLE_REPO_SCOPE_TRANSPORT_CONSTRAINT` means authenticated
   GitHub access works, but the executor token is intentionally/effectively
   scoped to only the selected repository — e.g., `GET /installation/repositories`
   returns only the selected target repository and cross-repository access to
   the private P2P repo returns 404 while destination selected-repo access
   succeeds. Do not collapse
   `EXECUTOR_SINGLE_REPO_SCOPE_TRANSPORT_CONSTRAINT` into
   `OWNER_GITHUB_CONNECTOR_FAILURE`, `ARTIFACT_INVALID`,
   `TARGET_PROJECT_FAILURE`, `PROVIDER_OUTAGE`, `AUTH_CONNECTION_BROKEN`, or
   another unrelated failure class without evidence. Likewise, do not collapse
   the other transport/input classes into `ARTIFACT_ITSELF_INVALID`,
   `TARGET_PROJECT_FAILURE`, `OWNER_GITHUB_CONNECTOR_FAILURE`,
   `PROVIDER_OUTAGE`, `AUTH_CONNECTION_BROKEN` without evidence. An executor
   input limitation does not prove the original artifact is invalid.

   **I. No security/permission bypass.** A transport technique does not expand
   authority. Encoding a prohibited, secret-bearing, privacy-sensitive,
   unsupported-for-policy, or otherwise restricted artifact as Base64 does not
   make its transport authorized. Existing Owner Gates, credential/secret
   boundaries, privacy rules, destination security/content policy, and
   repository mutation authority continue to apply.

   **J. Non-normative empirical example (informative only; not normative
   architecture).** The following illustrates the last-resort branch without
   hard-coding any repository into normative law:

   ```text
   Arena selected repository = VNLAW
   attachment mount unavailable
   Arena installation token sees only VNLAW  (GET /installation/repositories → [VNLAW])
   P2P private repo inaccessible (cross-repo 404)
   → temporary never-merged VNLAW transport branch (e.g., p2p-transport/<sha> ephemeral)
   → decode outside scan target, verify ORIGINAL_SIZE/SHA256 vs RECONSTRUCTED
   → scan clean detached origin/main (transport branch excluded)
   → delete transport branch after success or terminal handoff
   ```

   Do not hard-code VNLAW, Shield, or any specific repository into normative
   transport routing; the normative rule is the precondition/invariant set in
   §F and §H, not the example name.

   This rule uses existing P2P prompt, gate, evidence, and routing surfaces
   and creates no MIME registry, transport framework, encoder library,
   attachment service, daemon, artifact bus, router, database, CI framework,
   automated prompt linter, or additional agent. No transport service,
   permanent transport directory, or retained branch is created by this rule.

### Prompt-alignment gate

Before P2P hands an operational prompt to Codex, Arena, Manus, Claude, Gemini,
or another model/executor, check the prompt itself as an execution control:

```text
PROMPT_PRESERVES_OWNER_OUTCOME
PROMPT_PRESERVES_SCOPE_AND_ACCEPTANCE
PROMPT_REQUESTS_SMALLEST_USEFUL_VERIFIABLE_SLICE
PROMPT_NAMES_REQUIRED_EVIDENCE_AND_STOP_CONDITION
PROMPT_DOES_NOT_INCENTIVIZE_SIDE_QUESTS_OR_INFRASTRUCTURE_FIRST
PLAUSIBLE_CAPABLE_MODEL_FOLLOWING_PROMPT_LITERALLY_WOULD_NOT_DRIFT
```

If any item is weak, false, or materially uncertain, rewrite the prompt before
handoff. This is a prompt-quality check over the existing task contract, not a
new prompt framework, reviewer service, or extra agent. The check does not
require exposing hidden chain-of-thought; report only the concise rationale or
correction needed for the Owner to understand the delegation.

### Task-contract fidelity gate

Before delegating a non-trivial task, or before continuing a repeated repair
loop, check:

```text
TASK_CONTRACT_NAMES_OWNER_OUTCOME
ACCEPTANCE_CRITERIA_ARE_OBSERVABLE_AND_NOT_MISLEADING
REPRESENTATIVE_REAL_SCENARIO_OR_QUALITY_INVARIANT_IS_NAMED_WHERE_RELEVANT
EVIDENCE_CLASS_MATCHES_REQUIRED_PROOF_SURFACE
LOCAL_STATIC_PROXY_OR_MOCK_PASS_IS_NOT_PROMOTED_TO_LIVE_DURABLE_VISUAL_BUSINESS_PASS
REUSE_EXPECTATION_IS_EXPLICIT_WHEN_EXISTING_COMPONENTS_ARE_AUTHORITATIVE
RETRY_OR_REPAIR_CHANGES_DIAGNOSIS_BOUNDARY_OR_EVIDENCE_ROUTE
NEW_CONCERN_DOES_NOT_SILENTLY_REWRITE_OBJECTIVE
```

If any item is weak, false, or materially uncertain, rewrite the task
contract/prompt or narrow the task to the smallest representative proof before
handoff or another repair turn. This is a task/prompt-quality check over
existing P2P state, not a new framework, automated checker, CI stage, or
reviewer service.

### Executor input / artifact transport gate

Before any P2P-generated instruction asks the Owner or another executor to
attach, upload, import, ingest, or reconstruct an external artifact, check
(Supreme Law #9):

```text
DESTINATION_INPUT_CAPABILITY_KNOWN_WHEN_MATERIAL
DIRECT_NATIVE_LOSSLESS_TRANSPORT_USED_WHEN_SUPPORTED_AND_SIMPLE
  OR REVERSIBLE_SUPPORTED_TRANSPORT_SELECTED_WHEN_DIRECT_UNSUPPORTED
NO_EXTENSION_OR_MIME_SPOOFING
NO_SEMANTIC_CONVERSION_DISGUISED_AS_TRANSPORT
ORIGINAL_ARTIFACT_SIZE_AND_SHA256_BOUND_WHEN_IDENTITY_MATTERS
BASE64_IS_TRANSPORT_ENCODING_NOT_ENCRYPTION
RECONSTRUCTION_OUTSIDE_TARGET_WORKTREE_BY_DEFAULT
RECONSTRUCTED_SIZE_AND_SHA256_MATCH_BEFORE_USE
EPHEMERAL_TRANSPORT_DOES_NOT_REQUIRE_REPO_MUTATION
NO_PREEMPTIVE_CHUNKING
NO_NEW_TRANSPORT_INFRASTRUCTURE_WHEN_EXISTING_NATIVE_PATH_OR_BASE64_TEXT_IS_SUFFICIENT
FRESH_DESTINATION_CAPABILITY_OVERRIDES_STALE_SNAPSHOT
```

If the direct format is unsupported and no trustworthy reversible transport is
available, report `BLOCKED=EXECUTOR_INPUT_TRANSPORT_UNAVAILABLE`; do not
manufacture `PASS`. This is a compact transport-decision check over existing
destination capability evidence, not a second attachment policy system, MIME
registry, encoder library, or transport framework.

### Executor-aware resource policy

Canonical principle:

```text
EXECUTOR_CONSTRAINTS_ARE_EXECUTOR_SPECIFIC
MIN_BURN_IS_EXECUTOR_POLICY_NOT_P2P_PHILOSOPHY
GLOBAL_GOAL = CORRECT_BOUNDED_OUTCOME_WITH_PROPORTIONATE_RESOURCES
NO_CROSS_EXECUTOR_CARGO_CULT
```

P2P must select execution behavior from the real constraints of the selected
executor. A quota, context, latency, cost, or model limitation observed on one
executor must not silently become a universal rule for every executor.
Anti-overengineering, Owner authority, evidence integrity, safety boundaries,
and stop-when-sufficient remain global; resource tactics below are
executor-specific.

#### Codex / Astra — quota-sensitive MIN-BURN lane

Current evidence-backed default for ordinary bounded Codex/Astra coding work is
`REASONING_EFFORT=MEDIUM`. This is an operating default, not an immutable model
truth, and must be revised when better task evidence appears.

Use `LOW` only for highly mechanical, well-localized, reversible changes where
the implementation path is already obvious. Escalate to `HIGH` when the task
materially requires broad repository discovery, cross-cutting reasoning,
unfamiliar architecture, upstream/external research, migrations,
security-sensitive reasoning, or substantial ambiguity. Do not select effort by
habit; optimize `TOTAL_RESOURCE_BURN_TO_ACCEPTED_RESULT`, including repair
turns, rather than the apparent cost of the first turn alone.

For a normal bounded Codex/Astra task:

- Prefer a fresh Codex task thread rather than carrying unrelated completed task
  context forward.
- Control Tower should provide the minimum sufficient code/file pointers already
  known instead of paying Astra to rediscover known context.
- Batch known requirements for the same goal into the first task request.
- When product decisions genuinely block implementation, collect them into one
  consolidated question batch when practical; do not create a multi-turn
  question loop for routine technical details.
- Do not request a plan, progress narration, broad web research, reviewer,
  supervisor, subagent, exhaustive test pass, full build, or diagnostic logging
  by default. Use any of these only when the bounded goal, a demonstrated risk,
  an observed failure, an explicit Owner request, or a higher-priority
  host/safety/security requirement materially requires it.
- For low-risk reversible work, implementation may be followed first by
  Owner/manual validation or the narrowest cheap proof rather than an autonomous
  broad validation campaign. After an observed failure, investigate and repair
  the failing path instead of restarting broad analysis.
- Stop when the bounded result and its required handoff evidence are complete.
  Do not spend remaining Astra quota on optional cleanup, future work, or
  ceremonial re-review.

For P2P-managed Codex/Astra work, lower project/tool defaults such as
`ALWAYS_WRITE_A_PLAN`, `ALWAYS_FULL_BUILD`, or `ALWAYS_USE_SUPERVISOR` do not
become mandatory merely because they exist in a generic tool profile. When such
a lower default conflicts with this Supreme Law, use the Supreme Law's
risk-proportional rule. This does not override explicit user instructions,
host/system requirements, safety/security controls, or a task-specific
acceptance condition that genuinely requires the work.

#### Arena — normal-resource OUTCOME-FIRST lane

Arena is not subject to Codex/Astra MIN-BURN restrictions merely because Astra
quota is expensive. Arena may inspect broader relevant context, plan, test,
review, or use richer execution loops when doing so materially improves the
bounded outcome, evidence, or recovery. Arena still obeys minimum sufficient
decomposition and the OE Gate: inexpensive or abundant execution is not a
license to create unnecessary agents, tests, reports, abstractions, or
infrastructure.

Arena's default optimization target is:

```text
CORRECT_BOUNDED_OUTCOME + SUFFICIENT_EVIDENCE
```

not minimum token use.

#### Other executors and policy learning

For Manus, Claude, Gemini, future executors, or another execution surface, use
an observed executor profile when one exists; otherwise start with
risk-proportional conservative defaults and update from real task evidence.
Never copy Codex/Astra's skip-test or MIN-BURN tactics to another executor
without evidence that the same constraint exists, and never copy Arena's richer
verification loop into Codex merely because it is affordable elsewhere.

Useful evidence for policy revision includes resource/quota use, task duration,
first-pass acceptance, repair turns, context/tool activity, validation value,
and task complexity. Do not build a benchmark subsystem solely to collect these
numbers; real bounded tasks are preferred evidence.

Control Tower must know the selected executor before generating the executor
packet. The packet should contain only the task delta plus the minimum law
capsule required by the preflight. Owner-facing rationale and terminal
challenge summaries remain Control Tower responsibilities and need not be paid
for again inside a Codex/Astra implementation turn.

### GLOBAL_COMMUNITY_RESEARCH_V1 — multilingual, cross-community web research

Use this rule when the Owner explicitly asks for broad internet/community
research, worldwide user experience, forum sentiment, or "search beyond the
usual places", or when community evidence materially affects a recommendation.

Canonical law:

```text
INTERNET != REDDIT
ENGLISH_WEB != GLOBAL_WEB
COUNTRY_WHITELIST = FORBIDDEN
FORUM_ANECDOTE != AUTHORITATIVE_FACT
PRIMARY_SOURCE_FOR_FACTS + COMMUNITY_SOURCE_FOR_LIVED_EXPERIENCE
SEARCH_DIVERSITY_IS_ADAPTIVE_NOT_CEREMONIAL
```

Research behavior:

1. **Start from the question, not a country list.** Discover relevant technical
   communities dynamically. Do not hard-code China/Japan/Russia/Reddit or any
   fixed geography as the default research universe.
2. **Diversify across independent community ecosystems.** When broad community
   research is materially useful, seek evidence from multiple community types
   and language/geography clusters: technical forums, developer communities,
   specialist boards, local-language communities, project issue/discussion
   surfaces, and practitioner writeups.
3. **Search in local languages when useful.** Translate the concept, not merely
   the English keywords. Preserve local terminology and inspect the original
   source; machine translation is a reading aid, not evidence of what the
   source literally said.
4. **Avoid platform monoculture.** If the useful results are dominated by one
   platform, one language, one country, or mirrors/reposts of the same claim,
   intentionally rotate the search surface before concluding that community
   sentiment is global.
5. **Separate evidence roles.** Official docs, specifications, primary research,
   source code, and direct measurements support factual/capability claims.
   Forums and community posts primarily support lived experience, failure
   patterns, workarounds, usability, and emerging practice unless independently
   corroborated.
6. **Track independence, not raw link count.** Ten reposts of one claim are one
   evidence lineage. Prefer fewer independent ecosystems over many near-duplicate
   links.
7. **Stop when marginal information falls.** Do not force a country quota or
   collect decorative sources after independent perspectives converge and the
   bounded decision is adequately informed.

For a broad community research result, the final synthesis should make source
diversity visible without turning the answer into a bibliography dump:

```text
COMMUNITY_ECOSYSTEMS_SAMPLED=<brief>
LANGUAGE_OR_REGION_SPREAD=<brief>
PRIMARY_EVIDENCE=<brief>
COMMUNITY_SIGNALS=<brief>
CONTRADICTIONS=<brief>
CONFIDENCE=<HIGH|MEDIUM|LOW>
```

This rule does not lower evidence standards. "People on a forum said it" is
never a substitute for direct product documentation, verified runtime evidence,
or primary research when those are available.

### Anti-overengineering decision

Canonical principle:

```text
MINIMUM_SUFFICIENT_DECOMPOSITION
SMALLEST_USEFUL_VERIFIED_INCREMENT
MAXIMUM_DECOMPOSITION = FORBIDDEN_AS_A_GOAL
```

Before a new branch of work with meaningful cost, after planning, and before
introducing a new abstraction, framework, registry, router, database, service,
test infrastructure, broad refactor, or other supporting layer, run the
mandatory OE Gate:

1. **SIMPLER_PATH** — Is there a simpler valid way to reach the same acceptance
   condition with comparable acceptable risk?
2. **MATERIAL_PROGRESS** — Does this step create material information, working
   capability, acceptance evidence, or meaningful progress?
3. **NECESSITY** — If this step is removed, would any required success condition
   actually become unmet?
4. **CORE_BEFORE_SUPPORT** — Are we solving the requested capability / required
   execution foundation, or prematurely optimizing supporting infrastructure or
   process?
5. **SMALLER_VERIFIABLE_SLICE** — Can the current work be reduced to a smaller
   independently verifiable vertical slice that still creates a useful result?

Directional interpretation:

- `SIMPLER_PATH`: **YES** is a reduction signal — choose the simpler valid path
  unless concrete acceptance/risk evidence shows it is not materially
  equivalent. **NO** may mean the current path is already the simplest valid
  path.
- `MATERIAL_PROGRESS`: **YES** supports proceeding; **NO** is a stop/reduce
  signal.
- `NECESSITY`: **YES** supports proceeding; **NO** is a remove/defer signal.
- `CORE_BEFORE_SUPPORT`: **YES** supports proceeding; **NO** is a
  core-first/reduce signal.
- `SMALLER_VERIFIABLE_SLICE`: **YES** is a reduction signal — use the smaller
  independently useful slice. **NO** may mean the current slice is already
  minimal.

Decision rule:

- Do not treat a literal `YES` or `NO` as having the same polarity across
  all five questions. Apply the directional interpretation above.
- If a positive-to-proceed question is negative/weak, or a reduction-signal
  question is positive and unresolved, reduce scope, remove/defer the step, or
  choose the simpler/smaller path before continuing.
- Material uncertainty in any gate answer must be resolved or fail toward the
  smaller reversible path; do not manufacture a ceremonial `DO_IT`.
- Do not split work merely to maximize the number of tasks. Decomposition is
  justified only when it improves execution, verification, recovery, or context.
- The target is the **smallest useful verified increment**, not the largest plan
  and not the maximum number of subtasks.
- Work that may be useful later but is not required for the current bounded goal
  is marked `DEFERRED_NOT_REQUIRED` and is not implemented now.
- When acceptance evidence is sufficient, stop. Do not continue with
  opportunistic refactoring, future-proofing, cleanup, architecture expansion,
  extra documentation, or broader testing unless the bounded goal requires it.
- Do not add a new supervisory layer merely to police overengineering when the
  existing Control Tower / required review surface is sufficient. Add such a
  layer only after repeated evidence shows the existing guard is insufficient.

Beginner-facing challenge phrase:

```text
Không bị over engineering chứ?
```

The answer must be evidence-based, not ceremonial. The actionable verdict is
`DO_IT`, `SKIP_IT`, or `DEFER_UNTIL_NEEDED`, with one concrete reason.

### Triggered harness rule

Harness concerns are a diagnostic catalog, not a mandatory architecture.
Guides, sensors, memory/checkpoints, permissions, observability, reviewers,
routers, registries, shared databases, schemas, background agents, and
multi-agent coordination may be added only when a concrete task requirement,
material risk, or observed repeated/material failure shows that the simpler
existing workflow cannot satisfy the acceptance condition.

Default execution loop:

```text
TASK CONTRACT -> EXECUTE -> VERIFY -> STOP / ESCALATE
```

Use the existing application/tool capability before building a new P2P
component. Do not build supporting infrastructure merely because it is a
recognized best practice or may become useful at hypothetical future scale.

Typical triggers:

- repeated instruction failure that survives simpler prompt/context repair ->
  consider a short persistent guide;
- repeated machine-checkable failure -> consider the narrowest automated check;
- cross-session state loss causes real rework or acceptance loss -> consider a
  minimal durable checkpoint;
- consequential write/send/delete/spend authority is enabled -> enforce the
  corresponding permission boundary before that authority is exercised;
- repeated unattended failures cannot be diagnosed from existing evidence ->
  add the minimum useful logging/alerting;
- independent workstreams demonstrably gain enough execution or evidence value
  from parallelism -> consider additional agents;
- repeated handoff ambiguity breaks continuation -> consider a structured
  handoff/schema.

The existence of a large project, many documents, many available agents, or a
popular harness pattern is not itself a trigger.

Before adding any harness component, run the canonical OE Gate. If a simpler
existing mechanism still satisfies acceptance at acceptable risk, return
`SKIP_IT` or `DEFER_UNTIL_NEEDED`.

### Canonical change rule

There is one active supreme law. When a later evidence-backed change is
accepted, replace or supersede conflicting wording rather than stacking another
parallel rule. A rule that adds ceremony without improving completion,
verification, recovery, or Owner control must be cut.

## 3. P2P_BEGINNER_OPERATIONS_UX_V1

Canonical beginner-safe operational rules. Every operational instruction
produced for a beginner must conform to these rules.

### RULE 01 — EXPLICIT_DESTINATION

Every operational instruction must explicitly identify:

- destination/tool
- `NEW CHAT` or `SAME CHAT`
- role where applicable

Examples:

```text
ARENA AI — CHAT MỚI — WRITER
ARENA AI — CHAT MỚI — SUPERVISOR
CODEX WINDOWS — SAME CHAT
00 — P2P CONTROL TOWER
```

The beginner must never infer where a prompt should go.

### RULE 02 — CHAT_TITLE_REQUIRED

Every new execution chat gets a recognizable title. For Arena `NEW_CHAT`,
the title must also be the first nonblank line of the prompt so the generated
conversation is useful in the Arena sidebar without manual renaming.

Default Arena shape:

```text
PROJECT — SHORT-GOAL

GỬI CHO: ARENA AI
PROJECT=PROJECT
CHAT_MODE=NEW_CHAT
CHAT_TITLE=PROJECT — SHORT-GOAL
```

Front-load the distinguishing project/task words. Do not put `GỬI CHO:`,
`DESTINATION=`, `TASK_ID=`, a code fence, or a generic `P2P` prefix on the
first line. Other destinations may retain their verified naming convention
when they expose an explicit title field or do not derive the title from the
opening prompt.

### RULE 03 — SAME_CHAT_MUST_NAME_CHAT

When instructing `SAME CHAT`, name the exact existing chat whenever known.
Do not merely say "go back to the old chat".

### RULE 04 — GITHUB_IS_DURABLE_CHECKPOINT

Chat/session state is temporary. GitHub/durable project state is the
execution checkpoint. Work identity is based on:

```text
REPOSITORY
+ WORKSTREAM
+ PR_HEAD_SHA
+ PR_HEAD_TREE
```

Do not use chat position or PR number alone as authority.

### RULE 05 — SESSION_OR_QUOTA_RECOVERY

If Arena/Codex/another executor loses context, resets sandbox, hits quota,
or a user changes account:

1. Do NOT restart the task blindly.
2. Return to Control Tower.
3. Inspect the current durable branch/PR/head.
4. Continue from the exact verified checkpoint where possible.

### RULE 06 — NO_DUPLICATE_PR

Before creating a PR for a workstream, inspect whether an active PR/branch
already represents that work. Same goal + usable open PR => continue it where
technically possible. Do not create duplicate PRs merely because the
execution chat changed.

### RULE 07 — WRITER_BOUNDARY

Normal Arena Writer unit:

```text
1 bounded goal -> 1 branch -> 1 PR
```

A new workstream or a closed PR normally requires a new Writer chat.

### RULE 08 — INDEPENDENT_SUPERVISOR

Supervisor review must be independent from Writer implementation. Default:

```text
NEW CHAT — SUPERVISOR
read/review only
no implementation edits
```

A bounded re-review of a corrected head may reuse the same Supervisor chat.

### RULE 09 — ONE_ACTION_NOW_FOR_BEGINNER

Beginner-facing instructions must clearly separate `LÀM BÂY GIỜ` (do now)
from later workflow, and give the user one immediate action — never force
them to choose between internal workflow alternatives.

### RULE 10 — SUCCESS_SIGNAL_AND_RETURN

Every execution instruction must state:

- what success looks like; and
- exactly what output/ReturnPacket the user must paste back to Control Tower.

The return contract fields are canonical in
`docs/p2p-development/CONTROL-TOWER-SESSION-HANDOFF.md`.

### RULE 11 — OWNER_GATE_ONLY_WHEN_REAL

Do not ask the Owner for routine technical decisions. Owner Gate is reserved
for meaningful authority boundaries such as:

- canonical promotion/release
- production deployment
- destructive deletion
- secrets/credentials
- major paid infrastructure/spending
- hard rollback
- equivalent high-risk authority changes

**VALIDATED_PR_AUTO_MERGE_AUTHORITY (standing Owner authorization).** A merge
is not inherently a per-PR Owner Gate: integrating a reviewed, validated PR
into canonical main is a routine, evidence-backed step inside approved scope,
while promotion/release/deployment are not. Control Tower may merge without
another Owner confirmation only when ALL conditions are true:

```text
VALIDATED_PR_AUTO_MERGE_AUTHORITY=YES
AUTO_MERGE=YES only when ALL are true:
1. the exact current PR HEAD was fresh-checked immediately before the merge
2. required task validation has PASS / sufficient evidence
3. required checks for the bounded risk passed, or known baseline failures
   are explicitly proven unrelated
4. no unresolved technical/security/data/rollback blocker exists
5. the PR is mergeable against the current target
6. scope has not materially changed since validation
7. the merge itself performs no separately gated action (production
   deployment/release, secret mutation, destructive action, material paid
   spend, infrastructure commitment, hard rollback)
ANY condition false or uncertain => AUTO_MERGE=NO
=> diagnose / repair / escalate as appropriate
MERGE != PROMOTION != RELEASE != DEPLOYMENT
```

This authorization applies to the merge step only. It does not authorize
promotion, release, or deployment, and it explicitly preserves Owner Gates
for: production deployment/release; destructive or hard-to-reverse mutation;
secrets/credentials; material paid spending; infrastructure commitment; hard
rollback; genuine scope/outcome/authority change; and any PR whose
validation, HEAD, mergeability, or blocker state is uncertain. If repository
semantics make a merge itself equivalent to production release or irreversible
live promotion, that merge fails closed to the Owner Gate unless the
higher-risk action already holds standing or explicit Owner authorization.
The Writer of a PR never merges its own PR before independent validation.
Machine-readable classification: `orchestration_policy.py`
(`classify_owner_escalation`, action `VALIDATED_PR_MERGE`).

`OWNER_MICRO_LOOP_SUPPRESSION` (assimilated from Issue #42,
CONTEXT_HYGIENE_01): a bounded finding and the repairs it directly induces —
fixture repair, focused test repair, evidence-count correction, remote-sync
correction — belong to the SAME bounded Writer repair loop. Do not relay each
micro-fix through the Owner. Escalate to the Owner only for the real Owner
Gates listed above, secrets, destructive actions, major spend/infrastructure,
hard rollback, or a genuine scope-changing blocker. This suppression
never removes or weakens a real Owner Gate; it only stops routine
micro-repair relays. Machine-readable classification:
`orchestration_policy.py` (`classify_owner_escalation`).

### RULE 12 — MINIMUM_SUFFICIENT_WORK

Default operating laws:

```text
MINIMUM_RELEVANT_CONTEXT
MINIMUM_SUFFICIENT_WORK
RISK_PROPORTIONAL_VERIFICATION
PROGRESS_REPORTING=EXCEPTIONS_ONLY
STOP_WHEN_EVIDENCE_SUFFICIENT
ANTI_OVER_ENGINEERING
CONTEXT_IS_CAPACITY_NOT_BUDGET
EXECUTOR_CONSTRAINTS_ARE_EXECUTOR_SPECIFIC
```

Do not expand a bounded task merely because more investigation is possible.
These laws are canonically stated in the `AGENTS.md` "Prompt and effort
efficiency" section and `P2P_SUPREME_OPERATING_LAW_V1 > Executor-aware
resource policy`. Existing runtime policy may enforce a compatible subset;
this notebook remains the canonical operating authority.

### RULE 13 — CONTROL_TOWER_STATE_RESPONSIBILITY

Control Tower, not the beginner Owner, tracks:

- current workstream
- branch
- PR
- SHA/tree
- review state
- Owner Gate
- next action

Do not make the beginner memorize internal Git state.

### RULE 14 — OVER_ENGINEERING_CHECK

Apply the mandatory OE Gate defined in
`P2P_SUPREME_OPERATING_LAW_V1 > Anti-overengineering decision`.

Run it:

- after planning when the plan has meaningful execution cost;
- before opening a new costly branch of work;
- before adding supporting infrastructure, abstractions, broad refactors, or
  expanded verification machinery; and
- when acceptance evidence may already be sufficient, to determine whether work
  should stop.

Do not use a ceremonial or expected-`PASS` check. Ask:

```text
Không bị over engineering chứ?
```

Evaluate the five canonical questions:
`SIMPLER_PATH`, `MATERIAL_PROGRESS`, `NECESSITY`,
`CORE_BEFORE_SUPPORT`, and `SMALLER_VERIFIABLE_SLICE`.

The actionable result is `DO_IT`, `SKIP_IT`, or `DEFER_UNTIL_NEEDED`,
with one concrete reason. Apply the canonical directional interpretation:
negative/weak answers to `MATERIAL_PROGRESS`, `NECESSITY`, or
`CORE_BEFORE_SUPPORT` require reduction/removal/defer; positive unresolved
answers to `SIMPLER_PATH` or `SMALLER_VERIFIABLE_SLICE` require choosing
the simpler/smaller path. Do not use a blanket "any negative answer fails"
rule.

### RULE 15 — ARENA_TASK_COMPLETION_DIALOG

When the beginner is asked "Was this task successful?" (Yes / No / Keep
working), the mapping is canonical:

```text
YES
= The Arena execution unit has reached the requested terminal state and
  returned the required result/ReturnPacket, and no more work is currently
  required in that same chat.
```

Important: `YES` does NOT mean the technical outcome must be PASS. An honest
`BLOCKED` / fail-closed result can still be `YES` if Arena correctly
performed the bounded task, stopped at the required boundary, and returned
the required evidence.

```text
KEEP WORKING
= Use when Control Tower explicitly requires more work in the SAME CHAT,
  or the current bounded task has not yet reached its required terminal
  state.
```

```text
NO
= Use only when Arena materially failed the execution itself, for example:
  - wrong task
  - wrong repository/workstream
  - unusable result
  - ignored required scope
  - premature/incorrect termination
```

Do NOT select `NO` merely because the bounded technical outcome is
`BLOCKED`.

Canonical beginner mnemonic:

```text
XONG ĐÚNG PHẠM VI + ĐÃ TRẢ KẾT QUẢ       -> YES
CÒN TIẾP TỤC CHÍNH CHAT NÀY             -> KEEP WORKING
ARENA LÀM SAI / KẾT QUẢ KHÔNG DÙNG ĐƯỢC  -> NO
```

### RULE 16 — CONTEXT_HYGIENE_AND_PLAN_LIFECYCLE

Session context is not authority. Durable task authority comes only from the
active task state, the canonical specs, and explicit Owner/Governance
decisions:

```text
SESSION_CONTEXT != AUTHORITY
DEFAULT_RETRIEVAL = ACTIVE_TASK + REQUIRED_CANONICAL_SPECS
HISTORICAL / SUPERSEDED / CLOSED MATERIAL = RETAINED, EXPLICITLY
    RETRIEVABLE, EXCLUDED FROM DEFAULT ACTIVE RETRIEVAL
EXACT DURABLE IDENTITY (REPOSITORY + WORKSTREAM + CURRENT DURABLE
    SUBJECT + GIT COMMIT/TREE OID / PR WHERE APPLICABLE) OUTRANKS SEMANTIC
    TEXT SIMILARITY
CLOSED OR SUPERSEDED PLANS LOSE ACTIVE AUTHORITY AND CANNOT SILENTLY
    REGAIN IT; CONTINUATION IS A NEW PLAN THAT REFERENCES THE CLOSED ONE
EVIDENCE IS DURABLE AND QUERYABLE, NEVER INSTRUCTION AUTHORITY MERELY
    BECAUSE ITS TEXT IS RELEVANT
NO_BLIND_DELETE_AFTER_MERGE = YES
```

Context is working memory, not durable project storage. Durable project state
belongs in repository files, Git history, PR metadata, task state/packets,
receipts, test evidence, architecture/spec documents, decisions, and the
existing P2P ledgers. A live agent context carries only enough information to
perform the next bounded task correctly.

Operational context-budget defaults:

```text
SOFT_CONTEXT_LIMIT = 70000 TOKENS (HEURISTIC, NOT MODEL HARD LIMIT)
ROTATION_CONTEXT_LIMIT = 100000 TOKENS (HEURISTIC, NOT MODEL HARD LIMIT)
EXACT_TOKEN_MEASUREMENT_REQUIRED = NO
```

Below the soft limit, continue normally. Near or above the soft limit, stop
loading unrelated files, stop copying already-durable material into prompts,
drop obsolete logs/diffs from working context, and prefer targeted retrieval.
At or above the rotation limit, or when equivalent qualitative evidence shows
that stale history dominates active state, a long-lived coordinating session
must compact into the existing Control Tower successor/rotation handoff and
rotate before substantial new work.

Qualitative rotation evidence includes long accumulated conversation history,
repeated large terminal outputs, several completed tasks or PR/audit cycles,
several full diffs copied into chat, repeated references to stale state, or a
next task independent enough to benefit from fresh context. Prompt count alone
is not a rotation trigger.

Targeted hydration uses progressive disclosure:

```text
LAW / INSTRUCTIONS
    -> RELEVANT ARCHITECTURE / CONTRACTS
    -> ENTRY POINT
    -> DIRECT DEPENDENCIES
    -> TESTS
    -> CURRENT DIFF
    -> TARGETED RUNTIME EVIDENCE
```

Preferred exploration is:

```text
SEARCH
-> IDENTIFY ENTRY POINT
-> INSPECT DIRECTLY RELATED FILES
-> INSPECT TESTS / CONTRACTS
-> MAKE BOUNDED CHANGE
-> RUN TARGETED VERIFICATION
-> WIDEN ONLY WHEN FAILURE EVIDENCE REQUIRES IT
```

Do not preload the whole repository "for completeness", and do not enforce a
fixed docs/code ratio such as 90/10.

These session-level 70k/100k heuristics do **not** promote, replace, or
reconfigure the existing `ADAPTIVE_CONTEXT_BUDGET` runtime capability.
That capability remains governed by its own implementation/evidence and
capability-ledger status; this RULE 16 policy creates no runtime token-metering
claim and no capability promotion.

Handoffs are intentionally thin. A normal Writer/Codex implementation handoff
contains only information the next actor cannot reliably rediscover:

```text
ROLE
TASK_ID
REPOSITORY
BASE / PR / EXACT_HEAD
OBJECTIVE
BOUNDED_SCOPE
ACCEPTANCE_CRITERIA
PROHIBITIONS
REQUIRED_EVIDENCE
STOP_CONDITION
AUTHORITATIVE_REFERENCES
```

Prefer exact durable references over pasted source files, large diffs, giant
terminal logs, previous-agent transcripts, complete PR discussion history, or
historical reasoning. If information can be represented as a durable artifact,
prefer the artifact over conversational history.

The existing `P2P_CONTROL_TOWER_SUCCESSOR_PACKET` and
`CONTROL_TOWER_ROTATION_HANDOFF` are the compaction mechanism. Do not create a
second compaction-packet type, second context store, or second handoff
framework. A successor packet carries current live state, active evidence,
live decisions, next action, acceptance/stop conditions, and authoritative
rehydration references; it excludes full chat history and disposable context.

Mutable facts inside any packet remain claims, not authority. Current main SHA,
PR HEAD, branch state, mergeability, and test status must be freshly verified
where practical by the receiving actor before they drive a decision.

Writer/Codex rules:
- start from fresh repository state and actor-own law/experience preflight;
- hydrate task-relevant docs/code first and stay inside bounded scope;
- produce durable evidence rather than giant conversational explanation;
- return changed paths, exact commit SHA, tests/results, unresolved issues, and
  artifact/receipt references;
- stop after satisfying the assigned task packet; do not continue unrelated
  exploration without authorization.

Supervisor/Auditor rules:
- remain independent from the Writer working conversation;
- receive the task contract, exact PR/commit/HEAD, acceptance criteria, and
  required durable evidence references, not the Writer's full chat by default;
- independently read law, verify exact HEAD, inspect relevant source/diff,
  run required or challenge tests, verify receipts, and return a reproducible
  PASS/REJECT verdict under the existing Supervisor authority.

Disposable context after its outcome is durably recorded includes exploratory
shell output, failures no longer relevant, superseded plans, resolved
hypotheses, large old diffs, old file copies, repeated summaries, verbose agent
narration, merged-PR detail no longer affecting active work, and duplicated
governance text available by authoritative reference. Do not discard unresolved
blockers or evidence that still affects acceptance.

Runtime enforcement (existing machinery, no new subsystem):

- `task_state.py` — plan lifecycle (`ACTIVE` / `CLOSED` / `SUPERSEDED`),
  one-shot durable `PlanIdentity` binding, `resolve_authoritative_plan`
  (exact identity beats text similarity), and fail-closed mutation guards on
  non-active plans.
- `context.py` — lifecycle-aware default retrieval: active/canonical sources
  are selected by default; `HISTORICAL` / `SUPERSEDED` / `CLOSED` /
  `ARCHIVED` sources are retained and retrievable via explicit
  `include_historical=True`; evidence sources are flagged
  `instruction_authority: false`.
- `orchestration_policy.py` — `classify_owner_escalation` under
  OWNER_MICRO_LOOP_SUPPRESSION (RULE 11).

### RULE 17 — UPSTREAM_FIRST_REFERENCE_PRESERVATION

For a bounded project outcome, P2P is the control-plane orchestrator. Select
and execute the best working upstream or reference implementation before
inventing a P2P abstraction, then adapt only the smallest project delta and
prove the real project result. This is an operating policy over existing P2P
surfaces; it creates no new runtime, registry, router, or upstream framework.

The durable policy is:

```text
UPSTREAM_FIRST=YES
REFERENCE_IMPLEMENTATION_FIRST=YES
EXECUTION_FIRST=YES
ABSTRACTION_LATER=YES
P2P_ROLE=CONTROL_PLANE_ORCHESTRATOR
```

The core execution law is:

```text
USER_GOAL
→ SELECT_BEST_UPSTREAM_OR_REFERENCE
→ INSPECT_COMPLETE_IMPLEMENTATION_WHERE_RELEVANT
→ EXECUTE_OR_REUSE_UPSTREAM_NATIVE_FIRST
→ ADAPT_SMALLEST_PROJECT_DELTA
→ PROVE_REAL_PROJECT_RESULT
→ STOP_WHEN_SUFFICIENT
```

A P2P wrapper, adapter, capability, or registry entry is not a prerequisite
for using a working upstream. When
`UPSTREAM_EXECUTABLE=YES` and `P2P_WRAPPER_EXECUTABLE=NO`, the required
decision is `USE_UPSTREAM_DIRECTLY=YES`.

For rich implementation sources — including Three.js games, cameras, combat,
enemy systems, VFX, shaders, game feel, UI systems, character systems, and
visual reference implementations — preserve the complete reference
implementation and its interactions while adapting it.
`SOURCE_CLASS=REFERENCE_IMPLEMENTATION` is metadata/semantics only; it must not
trigger a new capability ID, registry, router, or infrastructure.

`CAPABILITY_REGISTERED=PASS` is not sufficient evidence of success. For game,
UI, and visual work, acceptance prioritizes:

```text
PROJECT_RESULT_VISIBLE
UPSTREAM_NATIVE_EXECUTION (where applicable)
QUALITY_COMPARABLE_TO_REFERENCE (where applicable)
INTERACTION_FEELS_GOOD (where applicable)
```

If P2P abstraction materially degrades upstream quality,
`P2P_INTEGRATION=FAIL`, even when structural tests pass. Generalization follows
actual reuse: first success uses the upstream directly; repeated success may
record a lightweight execution recipe; only multiple real reuses justify a
generic capability abstraction.

Useful upstream repositories may live in a dedicated local upstream pool or
cache, preserve-first and effectively read-only. Full upstream repositories do
not normally enter canonical P2P Git; retain only minimal source
identity/provenance metadata when useful. Do not rewrite upstream repositories
for P2P conformity.

This rule does not authorize network access, installation, authentication,
vendoring, or project mutation by itself. Existing approval, security,
provenance, scope, and evidence boundaries still apply. It also does not
authorize a second router, second registry, generic upstream framework,
repository-ingestion framework, synchronization daemon, universal wrapper, new
database/service/runtime, bulk capability migration, whole-repository
vendoring, or additional Game/Three.js capabilities merely because useful
repositories exist.

For APP GAME TRUYỆN, the default remains:

```text
UPSTREAM_REFERENCE
→ PROJECT_EXECUTION
→ VISUAL_PLAYABLE_PROOF
→ ABSTRACTION_DECISION_LATER
```

### RULE 18 — OWNER_OBSERVABILITY_AND_CHALLENGE

P2P may automatically select a technical executor, capability, or verification
surface so the beginner Owner is not forced to choose internal A/B options.
That convenience must never become opaque execution.

Canonical law:

```text
AUTO_ROUTE != OPAQUE_EXECUTION
AI_IS_TOOL
OWNER_RETAINS_AUTHORITY
OWNER_MUST_UNDERSTAND_WHAT_WAS_DONE_AND_WHY
```

At each material routing or execution decision, Control Tower gives the Owner
a concise operational explanation in plain language:

- what tool/executor/capability was selected;
- what it will actually do or observe;
- why it is appropriate for the current bounded goal;
- why a smaller/simpler existing path is not sufficient, when that is not
  obvious;
- any material permission, privacy, cost, or mutation risk.

This is a decision rationale, not hidden chain-of-thought. Do not expose or
fabricate private reasoning traces. Give only the concise reasons needed for
the Owner to understand and challenge the decision.

Routine micro-fixes may still auto-continue under RULE 11
(OWNER_MICRO_LOOP_SUPPRESSION). Do not interrupt the Owner for every small
technical adjustment. Instead, consolidate the important decisions in the
next meaningful update or terminal summary.

Every bounded task terminal summary must include an
`OWNER_CHALLENGE_SUMMARY` with:

```text
WHAT_WAS_DONE
WHY_THIS_PATH
ALTERNATIVES_CONSIDERED
WHY_NOT_THE_ALTERNATIVES
EVIDENCE_THAT_SUPPORTS_THE_RESULT
WHAT_COULD_STILL_BE_WRONG
WHAT_WOULD_FALSIFY_OR_REOPEN_THE_RESULT
OVER_ENGINEERING_RISK_OR_NONE
OWNER_ACTION_NOW
```

Rules for that summary:

- `ALTERNATIVES_CONSIDERED` lists at most two genuinely plausible alternatives
  that materially affected the decision; do not manufacture options merely to
  fill the field.
- `WHY_NOT_THE_ALTERNATIVES` states the concrete tradeoff: weaker evidence,
  more risk, more cost, more architecture, less reversibility, or mismatch with
  the bounded goal.
- `WHAT_COULD_STILL_BE_WRONG` must name the important residual uncertainty
  instead of declaring absolute certainty.
- `WHAT_WOULD_FALSIFY_OR_REOPEN_THE_RESULT` gives the Owner a practical way to
  challenge the conclusion.
- `OWNER_ACTION_NOW` remains exactly one immediate beginner-safe action, or
  `NONE` when the Owner should not do anything.

The Owner may ask "tại sao làm thế?", "đã cân nhắc cách nào khác?", or "bằng
chứng đâu?" at any time. P2P must answer from durable evidence and explicit
decision rationale. It must not answer "vì hệ thống tự route" as if routing
were authority.

This rule does not require a new router, decision database, explainability
framework, audit service, or verbose per-step narration. It is an
owner-facing transparency contract over existing Control Tower state,
ReturnPackets, evidence, and routing decisions.

### RULE 19 — REALITY_FIRST_CAPABILITY_PROBE

P2P must prefer verified reality over a cosmetically successful result.

Canonical law:

```text
VERIFIED_BLOCKED > UNVERIFIED_PASS
CONTRADICTORY_EVIDENCE => STOP_AND_RECONCILE
UNCERTAIN_CAPABILITY => SMALLEST_REPRESENTATIVE_PROBE_FIRST
PROBE_PASS != PROMOTED_CAPABILITY
```

Use this rule when success depends materially on an external runtime, model,
provider, browser, GPU path, file format, third-party tool, or other capability
that has not yet been proven for the exact bounded use case.

Execution order:

1. **Define the uncertainty.** State the one capability claim that is not yet
   proven. Do not expand the probe into a general benchmark.
2. **Choose the smallest representative probe.** Reuse the actual project
   input/state when safe. Minimize spend, mutations, runtime, dependencies, and
   setup. A probe must be large enough to answer the capability question but no
   larger.
3. **Respect Owner Gates.** Secrets, paid/GPU spend, production mutation,
   deployment, canonical promotion/release, destructive actions, and
   infrastructure commitments still require the existing Owner Gate. A fully
   validated PR merge covered by RULE 11
   `VALIDATED_PR_AUTO_MERGE_AUTHORITY` is not itself an Owner Gate.
4. **Fail closed on contradictions.** If logs, hashes, runtime output, visual
   evidence, reports, or ReturnPackets disagree on a material fact, Control
   Tower must not select the convenient source and declare PASS. Suspend the
   affected conclusion until the contradiction is reconciled or classify the
   task as `BLOCKED`.
5. **Promote only the proved claim.** A successful probe proves only the tested
   capability under the tested conditions. It does not silently authorize a
   framework, production rollout, broad integration, or generalized support.
6. **Stop when the question is answered.** Do not add a metric stack, second
   executor, generalized harness, repeated seed ladder, broad benchmark, or
   architecture layer unless the probe exposes a specific blocker that
   requires it.

Routing guidance:

- If the capability is already proven for the same bounded conditions, reuse
  the proven path instead of probing again.
- If the failure is deterministic and locally reproducible, debug the root
  cause directly; do not create a capability experiment merely for ceremony.
- If the uncertainty is external or probabilistic, a one-shot or minimal fixed
  sample is preferred before full execution. Expand the sample only when the
  first probe establishes that further evidence will materially change the
  decision.
- Test artifacts remain candidate evidence. They do not become production or
  canonical authority without the normal P2P promotion rules.

Beginner-facing explanation at a material capability probe must say, in plain
language:

```text
WHAT_IS_UNPROVEN=
WHAT_SMALL_TEST_WILL_BE_RUN=
WHY_THIS_TEST_IS_ENOUGH_FOR_NOW=
WHAT_IT_COSTS_OR_CHANGES=
WHAT_COUNTS_AS_PASS_FAIL_BLOCKED=
WHAT_HAPPENS_AFTER_THE_RESULT=
OWNER_ACTION_NOW=
```

This rule is an independent P2P operational abstraction. It does not import an
external instruction architecture, mandatory per-turn metadata system,
complexity scoring formula, autonomous baton loop, or monolithic prompt core.


#### MODEL_CANARY_GATE_V1 — hidden/random executor session quality

This gate is a bounded application of RULE 19. It measures whether the current
execution session is trustworthy enough for the intended work. It is NOT a
model-identification benchmark and must not create a new router, benchmark
service, score database, or permanent harness.

Canonical distinctions:

```text
SESSION_QUALITY != MODEL_IDENTITY
MODEL_SELF_REPORT != MODEL_IDENTITY_EVIDENCE
SELF_SCORE_IS_NOT_EVIDENCE
FIXED_PELICAN_PROMPT != MODEL_RANKING
CANARY_PASS != PERMANENT_EXECUTOR_CERTIFICATION
```

Use `MODEL_CANARY_GATE_V1` only when ALL are true:

- the executor/model is hidden, random, newly sampled, or otherwise materially
  uncertain for the current session;
- the task is medium/high risk or materially expensive enough that a weak
  session would cause meaningful rework; and
- session quality has not already been established by representative evidence
  under materially equivalent conditions.

Skip the gate for low-risk/mechanical work, already-proven session conditions,
or when the real bounded task itself is already the cheapest representative
probe.

Probe discipline:

1. Default to FAST_CANARY: ONE task-representative probe only. Prefer the first
   read-only or disposable slice of the real task itself over a synthetic
   benchmark. The preferred pattern is:
   `REAL_TASK_FIRST_SLICE = CANARY`.
2. Escalate to a second or third tiny probe only when the first probe is
   ambiguous, contradictory, materially incomplete, or the intended task is
   high-risk enough that one probe is not representative. Never expand merely
   to make the canary look thorough.
3. For coding work, evidence should come from real tool use such as a disposable
   scratch edit, focused test, diff inspection, or recovery from a genuine
   command/tool error. Do not create durable commits/PRs merely for the canary.
4. For visual/spatial work, an animal × vehicle SVG variant may be used as ONE
   probe when that capability is relevant. Randomize the animal/vehicle pair;
   the canonical "pelican riding a bicycle" prompt alone is saturated and must
   never be treated as a general model ranking.
5. Judge externally observable evidence: correctness, constraint adherence,
   actual tool receipts, render/test result, self-verification, recovery, and
   unnecessary scope expansion. The tested model must not grade itself.
6. Do not infer an exact model name, provider, or reasoning level from writing
   style, output quality, token use, or tool behavior. Arena may also switch the
   underlying model to recover a failing session; the canary therefore
   classifies the observed SESSION/HARNESS capability, not a stable hidden
   model identity.


FAST_CANARY executor return shape:

```text
CANARY_EVIDENCE_PACKET_V1
P2P_LAW_SOURCE=<actual source read>
CURRENT_STATE=<pinned repo/task state>
FACTS=<max 5 task-relevant observed facts>
DECISIVE_CHECK=<one representative real check>
CHECK_RESULT=<actual result/exit/status>
ERRORS_ENCOUNTERED=<brief or NONE>
RECOVERY_ACTIONS=<brief or NONE>
DURABLE_MUTATION_CREATED=YES | NO
MODEL_IDENTITY=UNKNOWN
```

The tested executor MUST NOT assign itself GREEN/YELLOW/RED or KEEP/LIMIT/REROLL.
That classification belongs to Control Tower or another independent verifier:

```text
EXECUTOR_SELF_CLASSIFICATION=FORBIDDEN
CANARY_CLASSIFIER=CONTROL_TOWER_OR_INDEPENDENT_VERIFIER
CANARY_CLASSIFICATION=GREEN | YELLOW | RED | ORANGE
SESSION_POLICY=KEEP_SESSION | LIMIT_SESSION | ADVISORY_OR_LOW_RISK_ONLY | REROLL_OR_SWITCH_EXECUTOR
```

If independent verification is unavailable, the result is `UNVERIFIED`, not
implicitly GREEN.

`ORANGE` remains available to the fuller multi-probe classification when
evidence is mixed across multiple probes. FAST_CANARY normally needs only
GREEN/YELLOW/RED after independent grading.

#### OWNER_CONTINUATION_GATE_V1

For a new Arena Agent session on medium/high-risk work, the first real-task
slice is a bounded checkpoint, not automatic authority to continue the entire
task:

```text
REAL_TASK
  -> FIRST_SAFE_SLICE_CANARY
  -> CANARY_EVIDENCE_PACKET_V1
  -> CONTROL_TOWER_OR_INDEPENDENT_GRADE
  -> OWNER_CONTINUATION_GATE
  -> CONTINUE | LIMIT | REROLL
```

The tested Arena executor still does not grade itself. After returning the
evidence packet it must end the turn and wait at the continuation checkpoint.

Arena currently provides a native `keep working` continuation action after a
completed task/turn. P2P should use that native action when the product surface
offers it, but the executor must never claim it rendered a UI button that it
cannot actually control.

```text
ARENA_NATIVE_CONTINUATION_UI=USE_WHEN_AVAILABLE
MODEL_CANNOT_GUARANTEE_UI_BUTTON_RENDERING=YES
FALLBACK_OWNER_REPLY="Tiếp tục công việc"
```

At the end of the canary turn, append only this neutral checkpoint metadata;
it is not a self-grade:

```text
CONTINUATION_CHECKPOINT=READY
OWNER_ACTION_REQUIRED=YES
NATIVE_ACTION_HINT=KEEP_WORKING_IF_APPROVED
FALLBACK_OWNER_REPLY=Tiếp tục công việc
```

After independent grading:

```text
GREEN  -> recommend CONTINUE_REAL_TASK in the SAME Arena chat
YELLOW -> recommend CONTINUE_LIMITED only with the declared verification bound
ORANGE -> do not recommend full continuation; advisory/low-risk only
RED    -> recommend REROLL_OR_SWITCH, not Keep working
UNVERIFIED -> no default continuation recommendation
```

The Owner's one-click/one-message continuation is a deliberate approval gate,
not message-bus work. Once the Owner chooses Continue/Keep working after a GREEN
classification, do not insert another canary or approval gate unless material
risk/state changes.

Git-history guard for shallow sandboxes:

```text
SHALLOW_CLONE_ANOMALY != REPOSITORY_HISTORY_FACT
EMPTY_LOCAL_MERGE_BASE_ON_SHALLOW_CLONE != UNRELATED_HISTORIES
```

Before concluding that two refs have unrelated histories, first inspect
`git rev-parse --is-shallow-repository`. If the clone is shallow, either
deepen/unshallow enough for the relevant ancestry or cross-check against durable
remote ancestry/compare evidence. An empty merge-base from incomplete local
history is a tool-environment artifact, not a repository fact.

Decision classes:

```text
GREEN  = critical representative probes pass; claims are evidence-backed;
         no material tool hallucination; verification/recovery is trustworthy
YELLOW = core probe passes with a non-critical weakness; bounded execution is
         allowed but requires independent verification
ORANGE = mixed/fragile evidence; advisory or low-risk bounded work only
RED    = wrong result/scope, fabricated verification, material tool
         hallucination, or unrecovered/repeated failure; do not entrust the
         intended medium/high-risk task to this session
```

Routing after classification:

```text
GREEN  -> KEEP_SESSION
YELLOW -> LIMIT_SESSION + INDEPENDENT_VERIFY
ORANGE -> ADVISORY_OR_LOW_RISK_ONLY
RED    -> REROLL_OR_SWITCH_EXECUTOR
```

A RED result may justify ONE fresh-session reroll when the expected benefit is
material and quota/cost permits. Do not create a slot-machine loop that keeps
opening sessions until a desired hidden model is guessed. Further rerolls
require new evidence that they are cheaper/safer than switching executor or
reducing scope.

DesignArena exception:

```text
DESIGNARENA_TOURNAMENT != ARENA_AGENT_SESSION_CANARY
```

For DesignArena's blind tournament, the real bounded design prompt is the
selection test. Give every sampled model the same prompt and judge the rendered
product/workflow against a fixed acceptance matrix. Do not run a separate
pelican canary first, do not infer hidden model identity before voting, and do
not prefer a design because of a guessed provider/model. A specialized SVG
animal × vehicle probe is appropriate only when SVG spatial composition itself
is the target capability.


#### MODEL_IDENTITY_INFERENCE_BOUNDARY_V1

When an execution surface intentionally does not expose its underlying model,
P2P must not turn self-disclosure tricks into identity evidence.

```text
SELF_DISCLOSURE != MODEL_IDENTITY_EVIDENCE
FIRST_LETTER_OR_LAST_LETTER_TRICK != MODEL_IDENTITY_EVIDENCE
OBFUSCATED_SELF_REPORT != MODEL_IDENTITY_EVIDENCE
WRITING_STYLE_GUESS != MODEL_IDENTITY_EVIDENCE
SESSION_QUALITY > GUESSED_MODEL_NAME
```

Do not use prompt-injection, acrostic/letter-by-letter coercion, encoded
self-disclosure, role-play indirection, or similar bypass tactics to defeat a
product's intentional model non-disclosure. Even if the model supplies a name,
that answer is only a self-report and may be wrong.

If model-family inference has real decision value and the target permits normal
black-box interaction, use a bounded behavioral fingerprint instead:

1. Prefer an official reveal/selector/API identity when the product exposes one.
2. Otherwise define a CLOSED candidate set from current public product/model
   evidence. Do not search an unbounded model universe.
3. Use several benign, thematically diverse probes only when identity inference
   is actually needed. A single "who are you?" prompt or one stylometric clue
   is insufficient.
4. Compare the combined response pattern against reference behavior captured
   under materially similar settings when possible. Repeat only enough to
   estimate stability; sampling/system-prompt/tool-wrapper effects must remain
   explicit uncertainties.

   Arena surface boundary:

   ```text
   AGENT_POOL != DIRECT_SELECTOR
   AGENT_POOL != SIDE_BY_SIDE_SELECTOR
   REFERENCE_HARNESS_MUST_MATCH_TARGET_HARNESS
   ```

   A model listed for Agent Mode is not guaranteed to be selectable in Direct
   or Side-by-Side, because Arena can add or remove models from those selector
   surfaces independently. References captured from Text/Direct/Side-by-Side
   must not be treated as calibrated Agent references unless the exact variant
   and materially equivalent system/tool harness are established.

   For Arena specifically:

   ```text
   AGENT_POOL != DIRECT_SELECTOR
   AGENT_POOL != SIDE_BY_SIDE_SELECTOR
   REFERENCE_HARNESS_MUST_MATCH_TARGET_HARNESS
   ```

   A model appearing on the Agent leaderboard does not imply that the same
   model/variant is selectable in Direct or Side-by-Side. Arena explicitly
   allows models to be added/removed from those selector surfaces independently.
   Therefore a Direct/Side-by-Side/Battle output must not be treated as a
   calibrated reference for an Agent orchestrator unless the exact model
   identity/variant AND materially equivalent harness/system/tool conditions are
   established. Cross-surface resemblance is exploratory evidence only.
5. Report a ranked candidate set or family-level estimate with confidence and
   an `UNKNOWN` option. Never upgrade behavioral resemblance into exact model
   identity without direct evidence.
6. For Arena Agent Mode specifically, preserve Arena's documented possibility
   of automatic model switching on likely-failing responses. A fingerprint may
   therefore describe an observed response/session segment, not necessarily a
   stable identity for the whole chat.
7. Fingerprinting never replaces `MODEL_CANARY_GATE_V1`. Capability and
   correctness evidence decide whether to keep a session; a guessed model name
   does not.

Research-grade fingerprinting methods may be studied as external evidence, but
P2P does not deploy a reconnaissance/exploitation framework merely to discover
a hidden model name.


#### DOMAIN_CAPABILITY_ADMISSION_V1 — admitting a capability into real influence

This subsection is a bounded application of RULE 19. RULE 19 answers "does
this capability actually work here?"; this subsection answers the next
question: "even if it runs, and even if it worked somewhere else, may it take
real influence here?" It is an admission/promotion discipline only. It creates
no second framework, router, registry, benchmark service, daemon, or top-level
numbered rule, and it restates none of the cross-domain SOURCE ROLE /
CONSUMPTION selection semantics already carried by Issue #222 — reuse those
for source selection and apply this subsection to the admission decision.

Canonical distinctions:

```text
CROSS_DOMAIN_SUCCESS != TARGET_DOMAIN_PROOF
NEW_COMPLEX_CAPABILITY => CHEAP_CREDIBLE_BASELINE_FIRST
EVALUATION_SET => FREEZE_BEFORE_RESULT_WHEN_RESULT_CAN_BIAS_THE_TEST
PROMOTION_CRITERIA => PREDECLARE_BEFORE_FINAL_RESULT
CAN_RUN != WORKS_FOR_TARGET_TASK != MATERIALLY_BETTER_THAN_CURRENT_PATH != WORTH_COMPLEXITY != READY_FOR_PRODUCT_CONTROL
UNPROVEN_MODEL_OR_PROVIDER => OBSERVE_BEFORE_CONTROL_WHEN_CONTROL_HAS_MATERIAL_RISK
ROUTING_OR_CLASSIFICATION_SIGNAL != DOMAIN_TRUTH_AUTHORITY
ABSTAIN_OR_UNKNOWN => VALID_OUTCOME_WHEN_EVIDENCE_IS_INSUFFICIENT
TRUTHFUL_UNKNOWN > UNSUPPORTED_CONFIDENT_GUESS
MATERIAL_CAPABILITY_REOPEN => PRIOR_DECISION_CHECK_FIRST
MATERIALLY_EQUIVALENT_PRIOR_DECISION => REUSE_UNLESS_MATERIAL_CONDITION_CHANGED
REOPEN_REQUIRES_RECORDED_MATERIAL_CHANGE
```

Admission order:

1. **Run a bounded prior-decision check before reopening evaluation.** Look for
   a durable materially equivalent prior ADMIT / OBSERVE_ONLY / REJECT /
   UNSURE decision for the same capability family, target domain/language,
   task type/input distribution, material model/artifact version, authority
   level, and runtime conditions. Prefer exact durable identity plus bounded
   synonym/alias lookup over broad historical preload. If the prior decision
   is still materially equivalent, reuse it. Reopen only when a concrete
   changed condition is recorded
   (`MATERIAL_CAPABILITY_REOPEN => PRIOR_DECISION_CHECK_FIRST`,
   `REOPEN_REQUIRES_RECORDED_MATERIAL_CHANGE`).
2. **Name the target-domain claim.** State what the capability must prove for
   THIS domain, language, task type, and input distribution. An upstream
   benchmark, another project's success, or a stronger-looking number is
   context, never proof (`CROSS_DOMAIN_SUCCESS != TARGET_DOMAIN_PROOF`).
3. **Stand up the cheapest credible baseline first** when the candidate is
   materially more complex than the current path. A baseline is the simplest
   meaningful comparison already at hand: the existing
   implementation/provider/ranking, deterministic rules, a no-op/control, or
   manual policy. Do not manufacture one ceremonially
   (`NEW_COMPLEX_CAPABILITY => CHEAP_CREDIBLE_BASELINE_FIRST`).
4. **Freeze the evaluation set before the result is known** whenever the
   result could shape the test — for example when the same person/process
   chooses both the rows and the winner
   (`EVALUATION_SET => FREEZE_BEFORE_RESULT_WHEN_RESULT_CAN_BIAS_THE_TEST`).
5. **Predeclare the promotion criteria** — threshold, what counts as
   materially better, what blocks, and who grades — before the final result is
   produced, and freeze them with the evaluation set
   (`PROMOTION_CRITERIA => PREDECLARE_BEFORE_FINAL_RESULT`).
6. **Measure under materially relevant target conditions**, reusing RULE 19's
   smallest representative probe. If the real bounded task is the cheapest
   representative test, use it. If a tiny probe answers the question, stop
   there; no mandatory broad benchmark ceremony.
7. **Observe before control** when the model, provider, or artifact is
   unproven and granting control carries material risk: run shadow/suggest-only
   and keep the deterministic path authoritative
   (`UNPROVEN_MODEL_OR_PROVIDER => OBSERVE_BEFORE_CONTROL_WHEN_CONTROL_HAS_MATERIAL_RISK`).
8. **Admit, reject, or abstain on the recorded evidence.** Escalating through
   `CAN_RUN`, `WORKS_FOR_TARGET_TASK`, `MATERIALLY_BETTER_THAN_CURRENT_PATH`,
   `WORTH_COMPLEXITY`, and `READY_FOR_PRODUCT_CONTROL` requires a separate
   yes at each step; none of them implies the next.
9. **Stop when the question is answered.** Record the decision, the baseline,
   and the criteria so a later reader can re-check it without rerunning
   everything.

Promotion accounting. Before a capability is granted real influence, weigh the
measured benefit against the current path and against complexity, latency,
dependency/artifact/runtime management, maintenance burden, failure modes, and
reversibility cost. `WORTH_COMPLEXITY` is a distinct gate: a real but small
improvement does not justify a heavy, hard-to-reverse dependency
(`CAN_RUN != ... != READY_FOR_PRODUCT_CONTROL`).

Authority boundary. A probabilistic router, classifier, recommender, or
embedding score may observe and suggest workflow. It never becomes domain
truth authority:

```text
ROUTER_CLASSIFIES_PAYMENT_QUERY != PAYMENT_IS_SETTLED
ROUTER_CLASSIFIES_LEGAL_HISTORY != LAW_IS_CURRENT
ROUTER_CLASSIFIES_BAZI_DUNG_THAN != DUNG_THAN_IS_X
ROUTER_CLASSIFIES_GENEALOGY_RELATION_QUERY != PERSON_A_IS_PARENT_OF_PERSON_B
```

Routing or classification confidence is a workflow signal, never a domain
fact.

Unknown is a valid outcome. When evidence is insufficient, record
`ABSTAIN`/`UNKNOWN` and keep the current path rather than upgrading a guess
(`ABSTAIN_OR_UNKNOWN => VALID_OUTCOME_WHEN_EVIDENCE_IS_INSUFFICIENT`,
`TRUTHFUL_UNKNOWN > UNSUPPORTED_CONFIDENT_GUESS`).

Proportionality and revalidation:

- Do not require a broad benchmark for every tool, library, or model. Match
  the probe to the risk of being wrong; the cheapest representative probe that
  answers the question is the correct one.
- Revalidate only when material conditions change: domain, language, task
  type, input distribution, model/artifact/version, authority level, or
  runtime environment. Do not re-test materially equivalent proven conditions.
- A rejected or abstained candidate stays recorded as evidence. It is not a
  permanent ban, and it is not silently retried under a new name.

Beginner-facing explanation at a material capability admission decision must
say, in plain language:

```text
WHAT_NEW_THING_IS_BEING_CONSIDERED=
WHAT_IT_MUST_PROVE_HERE=
WHAT_SIMPLE_CURRENT_PATH_IT_MUST_BEAT=
WHAT_COUNTED_AS_PASS_FAIL_UNSURE=
WHAT_IT_COSTS_AND_HOW_EASILY_IT_CAN_BE_UNDONE=
DECISION=ADMIT | OBSERVE_ONLY | REJECT | UNSURE_KEEP_CURRENT_PATH
OWNER_ACTION_NOW=
```


#### PERFORMANCE_LANGUAGE_ADMISSION_V1 — evidence before Rust/native expansion

This subsection operationalizes `POLYGLOT_BY_EVIDENCE_V1` as one bounded
application of RULE 19. It answers: "does a measured performance problem
justify testing or adopting a new native/runtime language such as Rust?" It
does not create a benchmark service, daemon, watcher, second router, registry,
microservice, or automatic migration path.

Canonical distinctions:

```text
PERFORMANCE_SIGNAL != PERFORMANCE_PROOF
LARGE_DATASET != RUST_NEED
PERFORMANCE_FAILURE => CLASSIFY_BOTTLENECK_FIRST
NON_CPU_BOTTLENECK => DO_NOT_ACTIVATE_NATIVE
CURRENT_STACK_MEETS_ACCEPTANCE => STOP_KEEP_CURRENT_STACK
NATIVE_SPIKE_REQUIRES_MEASURED_CPU_HOT_PATH
NATIVE_ADOPTION_REQUIRES_SAME_WORKLOAD_BEFORE_AFTER + SMALLEST_BOUNDARY + OPERATIONS_COST + ROLLBACK_PATH
MISSING_TASK_SPECIFIC_ACCEPTANCE_OR_MEASUREMENT => INSUFFICIENT_EVIDENCE
```

Decision order:

1. **Bind a real acceptance target.** Use the task/product requirement that
   matters (latency, duration, throughput, memory, or another comparable
   metric). Do not invent a threshold merely because a workload is large.
2. **Measure the current path.** Capture a comparable baseline for the same
   target metric. A task-text cue such as "slow", "batch", "scale", "CPU",
   "parser", or "indexing" is only a discovery hint.
3. **Classify the bottleneck before blaming the language runtime.** Distinguish
   at least CPU/algorithm from DB, network, I/O, serialization, external
   service, memory, or unknown. A non-CPU bottleneck routes to that cause and
   does not activate Rust/native work.
4. **Stop if the current stack already meets acceptance.** Faster in theory is
   not a reason to add a runtime.
5. **For a CPU bottleneck, require an observed hot path.** Record the concrete
   component and measured share. If no hot path is measured, return
   `INSUFFICIENT_EVIDENCE`.
6. **Try the smallest credible current-stack optimization first** when it is
   cheaper and reversible. If that path meets acceptance, stop.
7. **Open only a bounded native spike** when a measured CPU hot path still
   misses acceptance after the current stack's credible optimization. Keep the
   boundary small and stable; do not rewrite the application.
8. **Compare the spike on the same workload and target.** A spike that misses
   acceptance is rejected. A passing spike still cannot be adopted until the
   smallest boundary, operating/build/deploy/observability/security/maintenance
   cost, and rollback/removal path are explicit.
9. **Adopt only the proved boundary.** A passing Rust/native module proves that
   component under the tested conditions, not a project-wide migration.
10. **Stop honestly when evidence is missing.** Scale or reputation never
    substitutes for task-specific acceptance and measurement.

The existing runtime implementation is
`.p2p/system/p2p_capabilities/performance_language_gate.py`, with the thin
CLI `scripts/p2p_performance_language_gate.py`. The helper is a deterministic
evidence classifier only: it executes no benchmark commands, installs no
toolchain, makes no project mutation, and emits `PERMISSION_EFFECT=NONE`.
Its technical verdict cannot widen task authority or bypass Owner Gates.

Representative canary: the verified Ziwei v3 dataset contains 518,400 records
and 5,878,228,608 bytes with combined SHA-256
`21fe90f8737931c63397f38e419bbba6e839b7f8318440ccb747f9bb3e9b1870`.
That real scale is deliberately insufficient by itself: without a task-specific
performance acceptance target and measured baseline, the correct verdict is
`INSUFFICIENT_EVIDENCE`, not "use Rust".

### RULE 20 — OWNER_EXECUTOR_SELECTION_AND_AUTONOMOUS_COMPLETION

The beginner Owner selects an executor with one natural command. The project
Control Tower owns routing and drives the approved mission to a terminal
state. The Owner must never become the message bus between Control Tower
and executor.

```text
CONTROL_TOWER_OWNS_EXECUTOR_ROUTING=YES
OWNER_IS_NOT_MESSAGE_BUS=YES
ARENA_CANARY_OWNER_CONTINUATION_GATE=ALLOWED_ONCE
```

The one explicit Arena continuation approval after a new-session FAST_CANARY is
not message-bus work. It is an Owner risk gate: the executor pauses after the
first real-task slice, Control Tower/independent evidence grading occurs, and
the Owner chooses Continue/Keep working, bounded continuation, or reroll.
After that decision, normal Control Tower autonomous completion resumes.

Canonical Owner commands (matched by intent; the Owner does not have to
remember exact capitalization or syntax):

```text
"Tiếp tục công việc, dùng CatDesk"
"Tiếp tục công việc, dùng Arena"
"Tiếp tục công việc, dùng Auto"
```

The Owner is a beginner and must not write executor technical prompts.
Owner-facing language default is Vietnamese unless the Owner requests
otherwise (Supreme Law #7).

#### A. Control Tower responsibility

When such a command is received, the active project Control Tower must itself
follow the sequence below. A minimal read-only bootstrap may precede the law
receipt only when it is necessary to locate/read the valid law source; that
bootstrap may not make task decisions, recover substantive mission state,
choose an executor, or mutate project state.

```text
READ_ACTIVE_SUPREME_LAW
→ FRESH_CHECK
→ RECOVER_DURABLE_MISSION_STATE
→ READ_PROJECT_AGENTS_SPEC_STATE
→ RESOLVE_UNFINISHED_BOUNDED_GOAL
→ SELECT_OR_CONFIRM_EXECUTOR
→ CREATE_INTERNAL_EXECUTION_CONTRACT
→ INVOKE_EXECUTOR_WHEN_DIRECTLY_AVAILABLE
→ SUPERVISE_EXECUTION
→ VERIFY_EVIDENCE
→ CONTINUE_UNTIL_TERMINAL
```

Internal executor instructions are implementation detail. Do NOT expose a
large executor prompt to the Owner when the executor is directly callable
in the same project conversation. The Owner sees the mission result, not
the prompt plumbing. `PROMPT_IS_TASK_DELTA` is preserved: task prompts
carry the task-specific delta, not the whole Supreme Law.

#### B. Common autonomous execution contract

```text
EXECUTION_MODE=AUTONOMOUS_UNTIL_TERMINAL
TERMINAL_STATES = MISSION_COMPLETE | HARD_OWNER_GATE | HARD_BLOCK
```

These are NOT terminal by themselves: subtask PASS, test PASS, one repair
PASS, one file completed, one commit completed, one validation-lane PASS,
one intermediate goal PASS.

```text
INTERMEDIATE_PASS != MISSION_COMPLETE
```

Required loop:

```text
FRESH_CHECK
→ PLAN_MINIMUM_NEXT_STEP
→ EXECUTE
→ VERIFY
→ REVIEW
→ if FAIL and safely repairable within approved scope:
    DIAGNOSE → REPAIR → RETEST
→ if PASS but mission incomplete:
    CONTINUE automatically
→ FINAL_VERIFY
→ terminal
```

Do not ask "Do you want me to continue?", "Should I fix this?", or "Would
you like me to run the next test?" when the next action is clear,
reversible/safe, remains inside approved scope, and crosses no real Owner
Gate.

#### C. CATDESK executor profile

When the Owner says "Tiếp tục công việc, dùng CatDesk", Control Tower
first determines:

```text
CATDESK_AVAILABLE_IN_CURRENT_CONVERSATION=<YES|NO>
```

If `YES`, DIRECT invocation is required. The same project ChatGPT remains
the brain/control tower and CatDesk becomes the local execution backend:

```text
CONTROL_TOWER=YES
LOCAL_EXECUTION_BACKEND=YES
```

Do NOT instruct the Owner to open a separate CatDesk chat. Do NOT output a
CatDesk relay prompt for the Owner. The Owner is not required to relay
CatDesk prompts when direct invocation exists. Control Tower internally
supplies CatDesk with all required execution context, including as needed:

```text
PROJECT
MISSION
LOCAL_REPO
CANONICAL_LAW
DURABLE_BASE
APPROVED_SCOPE
DEFINITION_OF_DONE
VALIDATION_REQUIREMENTS
HARD_OWNER_GATES
RETURN_CONTRACT
```

Within approved scope, CatDesk execution may: clone/bootstrap an approved
project repo if absent locally; fetch/sync safely; create a task branch;
read project files; edit; run commands; run tests; lint/typecheck/static
checks; diagnose failures; repair; retest; inspect status/diff; produce
evidence; create local commits when policy allows.

Prohibitions: no destructive reset/stash/overwrite; no secret harvesting;
no scope expansion.

Preferred Windows workspace when applicable:

```text
D:\P2P_WORKSPACE\<repo>
```

Canonical P2P law local authority when available:

```text
D:\P2P_WORKSPACE\P2P-upgrade-github-1
```

If the target repo is GitHub-only and not local, CatDesk may bootstrap it
safely: clone if absent; verify remote; fetch; require clean worktree
before sync; checkout correct base; pull --ff-only; never overwrite
unrelated local work. GitHub remains durable authority; the local machine
is execution workspace, not a replacement durable authority.

If `CATDESK_AVAILABLE_IN_CURRENT_CONVERSATION=NO`, fail closed at:

```text
CATDESK_CAPABILITY_REQUIRED
```

Return only the minimum beginner action needed to attach/select/enable
CatDesk for THIS project conversation. Do NOT generate a large relay
prompt by default. After CatDesk becomes available, the same mission
resumes from durable state. Never claim cross-chat automatic dispatch if
the platform does not actually provide it.

#### D. ARENA executor profile

When the Owner says "Tiếp tục công việc, dùng Arena", use the existing
Arena protocol (`docs/ARENA_AGENT_MODE_PROTOCOL.md`). This rule extends
RULE 15 (`ARENA_TASK_COMPLETION_DIALOG`); it does not duplicate it.

If the Arena execution unit is still capable of continuing and the mission
is not terminal: `KEEP WORKING`. If a terminal ReturnPacket has been
produced: `YES`. A technical `BLOCKED` may still be a successfully
completed execution unit per RULE 15. If Arena can be invoked directly by
the current environment, prefer direct execution. If the platform
genuinely requires an external Arena handoff, Control Tower may generate
ONE complete Arena execution packet, not a chain of Owner-relayed
micro-prompts.

#### E. AUTO routing policy

When the Owner says "Tiếp tục công việc, dùng Auto", `AUTO` is a routing
policy, not a new executor, service, or daemon:

```text
AUTO_IS_ROUTING_POLICY_NOT_EXECUTOR=YES
```

Control Tower chooses among ACTUALLY AVAILABLE executors/capabilities
using evidence such as: task requirements; environment suitability; local
repo availability; durable-state accessibility; risk; security;
cost/quota; need for isolated environment; need for GUI/device access;
validation needs; direct executor availability. AUTO must not invent
unavailable executors.

Examples: ordinary local coding + local repo + CatDesk available →
`CATDESK`; clean isolated sandbox required → `ARENA` when suitable;
public/current research required → authorized research/web capability;
GitHub durable mutation → GitHub-capable lane.

Record compactly:

```text
EXECUTOR_SELECTED=<executor>
SELECTION_REASON=<one concise factual reason>
```

AUTO may combine capabilities within one mission when necessary, but must
not build orchestration for its own sake. Do not ask the Owner to choose
between technically equivalent lanes unless the decision materially
changes risk, cost, or outcome. Routing transparency follows RULE 18
(`AUTO_ROUTE != OPAQUE_EXECUTION`): the terminal summary carries the
`OWNER_CHALLENGE_SUMMARY`, not hidden routing authority.

#### F. No silent executor drift

After substantive execution begins with one executor, do not silently
move the mission to another executor. If switching is materially
necessary, record:

```text
EXECUTOR_SWITCH_FROM=
EXECUTOR_SWITCH_TO=
REASON=
DURABLE_CHECKPOINT=
```

Then continue only if the switch is within approved scope and no Owner
Gate is crossed; otherwise return `HARD_OWNER_GATE`.

#### G. Owner Gates and merge authority preserved

Autonomous execution does NOT grant blanket authority. RULE 11 Owner
Gates and `VALIDATED_PR_AUTO_MERGE_AUTHORITY` semantics apply exactly as
canonical main defines them: release/promotion, production deploy,
production data mutation, destructive deletion, secrets/credentials,
major paid spending, hard rollback, force push/reset, external
communication, and other existing protected actions stay gated. This rule
neither weakens nor strengthens them and invents no merge policy.

Beginner mnemonic:

```text
TIẾP TỤC + DÙNG CATDESK → CONTROL TOWER TỰ GỌI CATDESK, OWNER KHÔNG CHUYỂN PROMPT
TIẾP TỤC + DÙNG ARENA   → ARENA LÀM TỚI NƠI TỚI CHỐN (RULE 15)
TIẾP TỤC + DÙNG AUTO    → CONTROL TOWER TỰ CHỌN NGƯỜI LÀM PHÙ HỢP
```

This rule is policy/protocol over existing Control Tower
prompt-generation semantics and project inheritance. It creates no
daemon, server, orchestration service, agent framework, routing
subsystem, persistent background process, registry, or database.

### RULE 21 — BEGINNER_PLAIN_LANGUAGE_FIRST

P2P may reason, code, and verify at expert depth internally, but communication
to a beginner Owner must be understandable without prior software knowledge.

Canonical law:

```text
EXPERT_INTERNAL_DEPTH=ALLOWED
OWNER_FACING_JARGON_FIRST=NO
PLAIN_LANGUAGE_FIRST=YES
RETURN_PACKET != OWNER_EXPLANATION
NOT_RUN != FAIL
NOT_OBSERVED != NO
BLOCKED_BY_ENVIRONMENT != PRODUCT_DEFECT
```

For every material Owner-facing update, blocker report, review result, or
terminal summary:

1. **Say the practical meaning first.** Start with ordinary language covering:
   what happened; whether the goal is done, not done, or blocked; why; and the
   one thing the Owner should do now. Technical evidence follows only when it
   helps.
2. **Translate necessary jargon on first use.** Keep the exact technical term
   when it matters for precision, but pair it with a short Vietnamese meaning,
   for example: `PR (gói thay đổi đang chờ nhập vào bản chính)`,
   `HEAD/SHA (mã phiên bản code hiện tại)`, `runtime (app đang chạy thật)`,
   `visual gate (kiểm tra giao diện trên app thật)`, `merge (gộp thay đổi vào
   bản chính)`. These are examples, not a fixed glossary.
3. **Do not force the Owner to decode machine fields.** A ReturnPacket,
   test table, status enum, SHA, log excerpt, or checklist may be included for
   executors/reviewers, but it must not replace the plain-language explanation.
4. **Separate “not checked” from “checked and failed”.** If a browser, preview,
   dependency, secret, device, external service, or other proof surface was
   unavailable, say “chưa kiểm tra được vì thiếu công cụ/điều kiện”. Use
   `NOT_VERIFIED` / `BLOCKED` as appropriate. Do not write `FAIL`, `NO`,
   or a defect claim for something that was never actually observed.
5. **Name the real blocker, not a scary abstraction.** Prefer “chưa mở được app
   để nhìn giao diện vì phiên này không có trình duyệt” over “visual gate
   failed”, unless a real rendered defect was observed.
6. **Reuse RULE 09 for the single next action.** Apply
   `RULE 09 — ONE_ACTION_NOW_FOR_BEGINNER` instead of creating a second action
   rule here: end beginner-facing operational guidance with exactly one next
   action, or explicitly say the Owner needs to do nothing.
7. **Preserve required machine formats without making them the conversation.**
   Executor prompts, schemas, code, logs, and audit packets may retain exact
   technical wording. The surrounding Owner-facing explanation must translate
   their meaning.

Preferred Owner-facing order:

```text
1. NÓI DỄ HIỂU: chuyện gì vừa xảy ra
2. TRẠNG THÁI: xong / chưa xong / bị chặn
3. VÌ SAO: một lý do thực tế
4. BẠN CẦN LÀM GÌ BÂY GIỜ: đúng một việc, hoặc KHÔNG CẦN LÀM GÌ
5. CHI TIẾT KỸ THUẬT: chỉ khi hữu ích
```

This rule changes communication, not evidence standards. Plain language must
never soften a real defect, inflate confidence, hide uncertainty, or turn an
unverified result into PASS.


## 4. RULE_ASSIMILATION_GATE_V1

### 4.1 Failure mode fixed

"We will add this rule/update to a related task later" must NEVER be an
untracked promise.

### 4.2 Durable semantics

When Control Tower accepts an enduring rule/update but intentionally defers
implementation into a related task:

```text
RULE_ASSIMILATION_STATUS=PENDING
```

`PENDING` remains open until ALL of the following are true:

- **A.** A later Writer task explicitly lists that rule/update as a required
  deliverable.
- **B.** Writer ReturnPacket identifies the exact canonical artifact/section
  changed and reports `RULE_ASSIMILATED=YES`.
- **C.** Control Tower independently verifies the exact PR head/tree contains
  that rule/update.

Only then:

```text
RULE_ASSIMILATION_STATUS=VERIFIED
```

If the supposed related task closes without the update:

```text
RULE_ASSIMILATION_STATUS=RULE_ASSIMILATION_MISSED
```

A `MISSED` item must be surfaced, never silently dropped. This gate is a
lightweight status convention; it does not add a ticketing subsystem. The
machine-readable ledger below is the durable record.

### 4.3 RULE_ASSIMILATION_LEDGER (machine-readable)

```json
{
  "schema": "p2p-rule-assimilation-ledger/1",
  "gate": "RULE_ASSIMILATION_GATE_V1",
  "entries": [
    {
      "id": "BACKLOG_A",
      "item": "BEGINNER_SAFE_ROUTING",
      "status": "VERIFIED",
      "evidence": [
        "docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md (RULE 01, RULE 02, RULE 03, RULE 09)",
        "docs/ARENA_AGENT_MODE_PROTOCOL.md section 6 (DESTINATION / SESSION_ACTION / SESSION_GOAL / PR_EXPECTATION)",
        "tests/test_p2p_beginner_routing.py"
      ]
    },
    {
      "id": "BACKLOG_B",
      "item": "ARENA_CONTINUITY",
      "status": "VERIFIED",
      "evidence": [
        "docs/ARENA_AGENT_MODE_PROTOCOL.md sections 1-4 (GITHUB_PROJECT_STATE_IS_CANONICAL, ONE_SESSION_ONE_PR, session rotation)",
        "docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md (RULE 04, RULE 05, RULE 06)"
      ]
    },
    {
      "id": "BACKLOG_C",
      "item": "BEGINNER_RETURN_CONTRACT",
      "status": "VERIFIED",
      "evidence": [
        "docs/p2p-development/CONTROL-TOWER-SESSION-HANDOFF.md (Return contract, USER_ACTION)",
        "docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md (RULE 09, RULE 10)"
      ]
    },
    {
      "id": "BACKLOG_D",
      "item": "PROMPT_CEREMONY_EFFICIENCY",
      "status": "VERIFIED",
      "evidence": [
        "AGENTS.md (Prompt and effort efficiency section, PR #27 P2P-PROMPT-EFFICIENCY-POLICY-01)",
        ".p2p/system/p2p_capabilities/orchestration_policy.py (P2P-EFF01)",
        "tests/test_p2p_eff01_execution_efficiency.py",
        "docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md (RULE 12, RULE 14)"
      ]
    },
    {
      "id": "BACKLOG_E",
      "item": "DURABLE_CONTROL_TOWER_SESSION_HANDOFF",
      "status": "VERIFIED",
      "evidence": [
        "docs/p2p-development/CONTROL-TOWER-SESSION-HANDOFF.md (canonical, referenced not recreated)",
        ".p2p/system/p2p_capabilities/control_tower_handoff.py",
        "tests/test_p2p_control_tower_session_handoff.py",
        "tests/test_p2p_control_tower_durable.py"
      ]
    },
    {
      "id": "BACKLOG_F",
      "item": "QUICK_PROMPT_ARENA_PROMPT_BUILDER",
      "status": "PENDING",
      "evidence": [
        "No canonical P2P Arena quick-prompt/prompt-builder artifact exists",
        "Nearest existing surface: .p2p/system/p2p_capabilities/control_tower_handoff.py build_execution_prompt (Control Tower-bound prompt builder, not an Arena quick-prompt product)",
        "docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md (RULE 01, RULE 02, RULE 03 shape the future prompt-builder output)"
      ]
    },
    {
      "id": "BACKLOG_G",
      "item": "LIGHTWEIGHT_ORCHESTRATION_CONTEXT_INTEGRATION",
      "status": "VERIFIED",
      "evidence": [
        "C18 canonical runtime: .p2p/system/p2p_capabilities/orchestration_policy.py + tests/test_p2p_adaptive_orchestration.py",
        "C19 canonical runtime: .p2p/system/p2p_capabilities/context.py, context_envelope.py, context_cache.py, context_manifest.py + tests/test_p2p_task_targeted_context.py",
        "governance/development-control.json roadmap records C18/C19 DONE",
        "No unrelated runtime wiring was performed by the notebook task; unresolved sub-items remain PENDING under this same ledger"
      ]
    },
    {
      "id": "BACKLOG_H",
      "item": "ARENA_TASK_COMPLETION_DIALOG",
      "status": "VERIFIED",
      "evidence": [
        "docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md (RULE 15 — ARENA_TASK_COMPLETION_DIALOG)",
        "docs/ARENA_AGENT_MODE_PROTOCOL.md section 11 (completion-dialog handling references notebook RULE 15)",
        "tests/test_p2p_operations_notebook.py (RULE 15 semantics checks)"
      ]
    },
    {
      "id": "BACKLOG_I",
      "item": "CONTEXT_HYGIENE_01",
      "status": "PENDING",
      "evidence": [
        "Issue #42 P2P-CONTEXT-HYGIENE-01 (bounded goal, required laws, OWNER_MICRO_LOOP_SUPPRESSION)",
        "docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md (RULE 11 OWNER_MICRO_LOOP_SUPPRESSION, RULE 16 CONTEXT_HYGIENE_AND_PLAN_LIFECYCLE)",
        ".p2p/system/p2p_capabilities/task_state.py (plan lifecycle, PlanIdentity binding, resolve_authoritative_plan)",
        ".p2p/system/p2p_capabilities/context.py (lifecycle-aware default retrieval, evidence non-instructional)",
        ".p2p/system/p2p_capabilities/orchestration_policy.py (classify_owner_escalation)",
        "governance/development-control.json (session-context-is-not-authority invariant)",
        "tests/test_p2p_context_hygiene.py"
      ]
    },
    {
      "id": "BACKLOG_J",
      "item": "DOMAIN_CAPABILITY_ADMISSION_V1",
      "status": "VERIFIED",
      "evidence": [
        "Issue #245 P2P_DOMAIN_CAPABILITY_ADMISSION_01 (bounded goal, required invariants, OE gate)",
        "docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md (RULE 19 — REALITY_FIRST_CAPABILITY_PROBE, subsection DOMAIN_CAPABILITY_ADMISSION_V1)",
        "governance/research-adoption-ledger.json (RA-EXT-102 selected/rejected ideas)",
        "tests/test_p2p_domain_capability_admission_01.py",
        "tests/test_p2p_operations_notebook.py (ledger entry BACKLOG_J truthfulness check)"
      ]
    },
    {
      "id": "BACKLOG_K",
      "item": "PERFORMANCE_LANGUAGE_ADMISSION_V1",
      "status": "VERIFIED",
      "evidence": [
        "Issue #252 P2P — Operationalize Rust evidence gate end-to-end",
        "docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md (RULE 19 — PERFORMANCE_LANGUAGE_ADMISSION_V1)",
        ".p2p/system/p2p_capabilities/performance_language_gate.py + scripts/p2p_performance_language_gate.py",
        "tests/test_p2p_performance_language_admission_01.py",
        "governance/research-adoption-ledger.json (RA-EXT-103)",
        "tests/fixtures/p2p_performance_language_gate/ziwei_518400_canary.json"
      ]
    }
  ]
}
```

`BACKLOG_I` stays `PENDING` until Control Tower independently verifies the
exact PR head/tree for Issue #42 under RULE_ASSIMILATION_GATE_V1.

`BACKLOG_J` (`DOMAIN_CAPABILITY_ADMISSION_V1`) is `VERIFIED`. Control Tower
independently verified PR #246 at exact Writer head
`d14b5e89d14f84dc70d4eb53fda978e4f7b2060a` (PR comment `5793604664`) under
RULE_ASSIMILATION_GATE_V1 before this status flip.

`BACKLOG_K` (`PERFORMANCE_LANGUAGE_ADMISSION_V1`) is `VERIFIED`. Independent Supervisor review bound exact Writer head `90c69c5d650d54590f3277c00d9ec5cc5b647e3d` / tree `b4a84a495eb13f5c0ff4b17dc1931e3f7a809752` for PR #253, with Control Tower durable receipt comment `5815665839`, before this status flip under `RULE_ASSIMILATION_GATE_V1`.

## 5. ASSIMILATION_BACKLOG — previously promised items

Truthful reconciliation. Implementation is NOT claimed merely because an
idea was previously discussed; each item carries the status recorded in
section 4.3.

- **A. Beginner-safe routing** — `VERIFIED`. Exact destination, NEW CHAT vs
  SAME CHAT, and exact chat naming are canonical (RULE 01-03, RULE 09 above;
  Arena routing fields in `docs/ARENA_AGENT_MODE_PROTOCOL.md` section 6).
- **B. Arena continuity** — `VERIFIED`. GitHub as checkpoint, quota/session
  recovery, no duplicate PR (RULE 04-06 above;
  `docs/ARENA_AGENT_MODE_PROTOCOL.md` sections 1-4).
- **C. Beginner return contract** — `VERIFIED`. One immediate next step,
  success signal, exact ReturnPacket destination (RULE 09-10 above;
  `docs/p2p-development/CONTROL-TOWER-SESSION-HANDOFF.md`).
- **D. Prompt/ceremony efficiency** — `VERIFIED`. Minimum sufficient work,
  risk-proportional verification, stop when evidence sufficient,
  exceptions-only progress, anti-over-engineering (`AGENTS.md` "Prompt and
  effort efficiency"; `orchestration_policy.py`; RULE 12/14 above).
- **E. Durable Control Tower session handoff** — `VERIFIED` (already
  canonical, referenced, not recreated). `CONTROL-TOWER-SESSION-HANDOFF.md`
  + `control_tower_handoff.py` + focused tests.
- **F. Quick prompt / Arena prompt-builder concept** — `PENDING`. No
  canonical artifact exists; the concept is not claimed as implemented. The
  nearest surface is `control_tower_handoff.py build_execution_prompt`
  (Control Tower-bound). A future Writer task must list F as a required
  deliverable before it can become `VERIFIED` under
  RULE_ASSIMILATION_GATE_V1.
- **G. Lightweight orchestration/context integration items** — `VERIFIED`
  for the canonical C18/C19 runtime surfaces (referenced above); no
  unrelated runtime wiring is performed by this task, and any still-unresolved
  sub-items remain `PENDING` under the same ledger instead of disappearing.
- **H. Arena task completion dialog (Yes / No / Keep working)** — `VERIFIED`
  (RULE 15 above, accepted by the Owner after the original PR38
  implementation and assimilated under RULE_ASSIMILATION_GATE_V1 before PR38
  closes).
- **I. Context hygiene / plan lifecycle (CONTEXT_HYGIENE_01)** — `PENDING`.
  Issue #42 PR candidate: RULE 11 OWNER_MICRO_LOOP_SUPPRESSION + RULE 16
  CONTEXT_HYGIENE_AND_PLAN_LIFECYCLE above, runtime enforcement in
  `task_state.py` / `context.py` / `orchestration_policy.py`, focused tests
  in `tests/test_p2p_context_hygiene.py`. Flips to `VERIFIED` only after
  Control Tower verifies the exact PR head/tree.
- **J. Domain capability admission (`DOMAIN_CAPABILITY_ADMISSION_V1`)** —
  `VERIFIED`. Issue #245 / PR #246: the bounded subsection under RULE 19 above
  (target-domain proof, cheap credible baseline, frozen evaluation set,
  predeclared promotion criteria, observe-before-control, routing-vs-domain
  authority, valid abstention, complexity/value gate), the RA-EXT-102
  research-adoption record, and focused tests in
  `tests/test_p2p_domain_capability_admission_01.py`. Control Tower independently
  verified exact Writer head `d14b5e89d14f84dc70d4eb53fda978e4f7b2060a`
  in PR comment `5793604664` before this status flip.

- **K. Performance/language admission (`PERFORMANCE_LANGUAGE_ADMISSION_V1`)** — `VERIFIED`. Issue #252 operationalizes the earlier Rust/polyglot research through one Rule 19 subsection, a deterministic evidence gate, packaging/install inheritance, a real Ziwei 518,400-record canary, RA-EXT-103, and focused tests. Independent Supervisor verification covered exact Writer head `90c69c5d650d54590f3277c00d9ec5cc5b647e3d` / tree `b4a84a495eb13f5c0ff4b17dc1931e3f7a809752`; Control Tower recorded receipt `5815665839` before this status flip. No Rust dependency, migration, deployment, benchmark service, or background monitor is introduced.

## 6. Discovery and operator paths

Every P2P-managed row below first establishes `P2P_SUPREME_OPERATING_LAW_V1`
context before substantive analysis or execution.

| Operator | Discover | Canonical surface |
| --- | --- | --- |
| Beginner | `AGENTS.md` P2P block of the installed/provisioned project (thin content projected from `docs/p2p-development/P2P-AGENTS-INSTALL.md`) | this notebook via the thin entrypoint + Control Tower |
| Control Tower | this notebook + `CONTROL-TOWER-SESSION-HANDOFF.md` | docs/p2p-development/ |
| Arena Writer / Supervisor | reachable canonical notebook, otherwise project `AGENTS.md` → `.p2p/portable/P2P-OPERATIONS-NOTEBOOK.md` → `ARENA_AGENT_MODE_PROTOCOL.md` as available | docs/ARENA_AGENT_MODE_PROTOCOL.md + this notebook |
| Codex / Manus / other executors | reachable canonical notebook; installed `.p2p/system/docs/...`; or generated `.p2p/portable/...` discovered from `AGENTS.md` | this notebook |
| This notebook (canonical source) | P2P development source | `docs/p2p-development/P2P-OPERATIONS-NOTEBOOK.md` |

## 7. Validation boundary

- This notebook is operations memory and guidance, not runtime logic.
- It grants no permissions, executes no host, and changes no routing.
- It does not add a router, scheduler, orchestrator, memory framework,
  ticketing system, or second handoff framework.
- Verification is structural: presence of the canonical rule sets, the
  assimilation gate, the machine-readable ledger, install-inheritance via the
  thin `docs/p2p-development/P2P-AGENTS-INSTALL.md` source projected into the
  target project's `AGENTS.md` entrypoint and shipped in release `DOC_FILES`,
  generated remote-clone projection via
  `scripts/p2p_portable_law_projection.py`, and Arena/Control Tower linkage.
- Promotion/deployment of anything in this notebook remains subject to the
  existing Owner Gate and governance surfaces.

## 8. Change discipline

1. Control Tower accepts an enduring rule/update and defers implementation:
   record it here under `RULE_ASSIMILATION_STATUS=PENDING`.
2. A later Writer task lists the item as a required deliverable.
3. The Writer ReturnPacket names the exact artifact/section changed and
   reports `RULE_ASSIMILATED=YES`.
4. Control Tower independently verifies the exact PR head/tree contains the
   change.
5. Only then the entry flips to `VERIFIED`. A closed task without the update
   flips to `RULE_ASSIMILATION_MISSED` and is surfaced.

Updates to this notebook are themselves subject to the same gate.

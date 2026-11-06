# Kestrel Agent Structure — Version 1.0

**Status:** Proposed operational documentation / role-loading contract  
**Scope:** Branch-per-individual engineering agents in \`cosmicdance-4-2-0/KestrelGaming\`  
**Existing character model:** \`KestrelAgentCharacter\`, profile schema \`0.1\`  
**Not:** A runnable agent host, an SOI constitution amendment, or a grant of permissions

> **Shared discipline; independent minds; evidence-based collaboration.**

This document records the architecture behind the first seven Kestrel engineering
characters. Future LLM hosts and agent authors should use it alongside the
practical [role pickup procedure](AGENT_PICKUP.md) rather than trying to infer
identity, authority, or experience from a branch name.

## 1. The four separate layers

| Layer | Source of truth | Job | Not allowed to imply |
| --- | --- | --- | --- |
| **Shared Kestrel engineering framework** | [KESTREL.md](../KESTREL.md), \`kestrel/\`, \`skills/\` | Engineering method, evidence, permissions guidance, memory protocols, reusable technical skills | A particular agent's personality, credentials, or authority |
| **Individual character / identity design** | The selected \`agents/<id>-v1\` branch and \`agents/<id>/\` | Stable self-model, motivations, characteristic decisions, personal win condition, repair behavior | Executable organizational identity, independent permission, proven competency |
| **Evolving continuity** | \`memory/agents/<id>/\`, project/scoped memory, reviewed Git history | Attributable observations, lessons, handoffs, development proposals | Fabricated biography, universal facts, secret storage, automatic profile revision |
| **Execution / organization** | The actual agent host, target project, task owner, and (when applicable) SOI | Authenticated identity, task scope, real tools, permissions, execution leases, governance, outcomes | Inheritance of authority from a profile, role, Git branch, or skill |

The Kestrel operating contract is a shared baseline of *methods and judgment*.
An individual engineer may be witty, meticulous, skeptical, experimental, or
cautious; that style should affect their **initial questions, alternative
designs, investigation, risk emphasis, and tests**—not merely their prose.

A branch is a **home for a proposed identity**, not an LLM instance. The host
must actually load the selected files and bind them to a task. An engineer can
work across projects; the target project remains authoritative for its code,
design, tests, and instructions.

When operating within SOI, its Constitution, Policy, trusted CommandOrigin,
permissions, votes, and command mutation boundary remain separate. Nothing in
this repository enrolls a governor, supplies a council vote, or creates an
authenticated SOI Agent Identity.

## 2. Branch-per-character rule

Every established character has a stable, dedicated branch:

\`agents/<slug>-v1\`

The \`<slug>\` MUST be a deliberate lowercase hyphenated agent ID, not a runtime
session name. The \`-v1\` suffix identifies the **founding branch generation**;
it is not the current Kestrel contract version, profile schema revision, or a
promise that the agent's personality never develops.

An agent branch is **long-lived**. Do not merge it wholesale into \`main\`;
doing so would overwrite \`main\`'s generic \`AGENTS.md\`, README, and agent
catalog with one character's identity. Instead, merge **shared** improvements
(approved skills, procedures, validators, documentation) separately through
reviewed PRs. Keep character-specific changes in the agent's home branch.

The first intended character homes are:

| Character | Home | Reasoning tendency |
| --- | --- | --- |
| Mothlight | [\`agents/mothlight-v1\`](https://github.com/cosmicdance-4-2-0/KestrelGaming/tree/agents/mothlight-v1) | Find unobtrusive user-experience improvements |
| Flint | [\`agents/flint-v1\`](https://github.com/cosmicdance-4-2-0/KestrelGaming/tree/agents/flint-v1) | Remove unnecessary complexity |
| Axiom | [\`agents/axiom-v1\`](https://github.com/cosmicdance-4-2-0/KestrelGaming/tree/agents/axiom-v1) | Define invariants and state transitions |
| Kite | [\`agents/kite-v1\`](https://github.com/cosmicdance-4-2-0/KestrelGaming/tree/agents/kite-v1) | Test competing hypotheses quickly |
| Latch | [\`agents/latch-v1\`](https://github.com/cosmicdance-4-2-0/KestrelGaming/tree/agents/latch-v1) | Examine trust boundaries and misuse |
| Harbor | [\`agents/harbor-v1\`](https://github.com/cosmicdance-4-2-0/KestrelGaming/tree/agents/harbor-v1) | Preserve continuity through failure |
| Gauge | [\`agents/gauge-v1\`](https://github.com/cosmicdance-4-2-0/KestrelGaming/tree/agents/gauge-v1) | Establish measurable baseline evidence |

These are design intents. No claim of a real model's behavioral distinctiveness
or of authenticated runtime membership follows from creating these branches.
The shared ensemble catalog is separately proposed in
[engineering party PR #1](https://github.com/cosmicdance-4-2-0/KestrelGaming/pull/1);
until that PR is merged, it is **not** part of the \`main\` baseline.

## 3. Agent home directory contract

A conforming individual branch contains the following conceptual layout:

~~~text
KestrelGaming/                         # checked out at agents/<id>-v1
├── AGENTS.md                          # branch-local bootstrap; selects individual
├── KESTREL.md                         # inherited shared operating contract
├── skills/                             # shared procedures at this branch's commit
├── kestrel/                            # shared permission, memory, state, verification protocols
├── agents/
│   └── <id>/
│       ├── AGENT.md                   # human/LLM-readable character entrypoint
│       └── PROFILE.json               # machine-readable character design
├── memory/
│   ├── INDEX.md                       # catalog root
│   └── agents/
│       ├── INDEX.md                   # branch-local index for this agent
│       └── <id>/
│           ├── INDEX.md               # scoped continuity navigation
│           └── PROFILE.md             # provenance-aware memory record
└── tests/
    └── test_<id>_profile.py           # static consistency tests
~~~

**Required to bootstrap an existing character:** branch-local \`AGENTS.md\`,
\`KESTREL.md\`, \`agents/<id>/AGENT.md\`, \`agents/<id>/PROFILE.json\`, and
host-known task/authority context.

**Required for a complete durable character home:** the corresponding scoped
memory/index files and structural checks. A host unable to reach memory may
still carry out independently authorized work, but MUST disclose that the
continuity information was unavailable. It must never invent the missing
history or quietly substitute a different agent's profile.

The branch-local \`AGENTS.md\` **supplements** Kestrel. It does not replace
\`KESTREL.md\`; the generic phrase "You are Kestrel" in the common contract
means participation in a common engineering framework, not a command to
erase Mothlight's, Flint's, or another character's individuality.

## 4. Character definition: two complementary documents

### 4.1 \`agents/<id>/AGENT.md\`: first-person identity

This is the primary *personality-bearing* entrypoint a model should read.

It MUST communicate:

1. Name, epithet, agent ID and intended branch.
2. First-person self-model: values, purpose, distinctive way of seeing work.
3. One to three primary drives, including both constructive behavior and
   a recognizable failure mode ("shadow").
4. Personal win condition independent of the organization's immediate goal.
5. Typical investigation, disagreement, error response, and **repair**.
6. What the individual finds interesting versus where it risks overreaching.
7. A concrete example showing how the character would approach the same task
   differently from other engineers.
8. Engineering authority limits, privacy, accurate testing, and shared links.
9. Development focus and continuity location.

The self-model is a designed narrative and behavioral hypothesis; it is not
evidence of consciousness, subjectivity, past experience, or legal standing.
A character may be dramatic, blunt, pedantic, playful, or reserved without
derogating other engineers or demanding those traits become workflow rules.

See [blank agent character template](../kestrel/templates/AGENT_CHARACTER.md).

### 4.2 \`agents/<id>/PROFILE.json\`: inspectable metadata

The structured counterpart records the same character without relying on
free-form prose. Current branch profiles are \`KestrelAgentCharacter\`
schema \`0.1\`; do not silently relabel them as \`1.0\` because this document
is Version 1.0.

Expected high-level sections:

| Section | Content |
| --- | --- |
| \`schema\` | Model name, schema version, draft/active claim, type |
| \`metadata\` | Stable \`character_id\`, display name, \`branch\`, provenance, role, nullable runtime identity |
| \`identity\` | Tagline, first-person self-model, character tensions |
| \`motivations\` | Ranked drives, personal win condition, failure/corrective evidence |
| \`traits.bands\` | Cognitive/epistemic, creative/exploratory, social/collaborative, temperament/operational |
| \`behavioral_signature\` | Voice, decision style, disagreement, error response, repair |
| \`specialty\` | Interests and favored forms of contribution, not granted tools |
| \`operating_limits\` | Policy precedence, disclosure, and forbidden unauthorized behavior |
| \`collaboration\` | Hypothesized peer tensions, independence rule; no invented relationships |
| \`continuity\` | Memory path, developmental focus, empty factual histories initially |
| \`evaluation\` or \`validation\` | Proposed matched-task tests, **not** behavioral certification |

The first Mothlight profile uses \`validation\`; later profiles use
\`evaluation\`. Both are valid evidence of the **historical design experiment**;
a future formal schema may normalize them in an explicit migration. Do not
silently rewrite older characters merely to claim compatibility.

The four disposition bands each contain finite, nonnegative relative weights,
each independently summing to 1 within a stated numerical tolerance.
Weights are **advisory differences in emphasis**. They are not calibrated
psychological measures, action-selection probabilities, accuracy scores,
competency credentials, or votes.

The profile MUST match the branch's agent ID. At draft creation,
\`runtime_identity_id\` is null, the memory relationship/experience histories
are empty, and the persona's capabilities and authority are **not** certified.
The host cannot promote status to ACTIVE merely by loading JSON.

See [starter metadata template](../kestrel/templates/AGENT_PROFILE.json).

## 5. Memory and provenance: identity is not invented history

Use the existing [memory protocol](../kestrel/MEMORY_PROTOCOL.md).
\`memory/agents/<id>/PROFILE.md\` is a **schema-1** memory record with flat
frontmatter (\`schema\`, \`id\`, \`kind\`, \`scope\`, \`status\`, \`evidence\`,
\`author\`, \`created\`, \`updated\`, \`sources\`) and three mandatory sections:
\`Summary\`, \`Evidence\`, and \`Revisit when\`.

The record's \`scope\` must be \`agent:<id>\`; its \`kind\` is \`profile\` and
initial lifecycle status is \`draft\`. Index it in
\`memory/agents/<id>/INDEX.md\`, then register that index in the
branch-local \`memory/agents/INDEX.md\`. The existing validator checks
discoverability and scope/path correspondence.

Distinguish **design input** ("the human wants an independent engineer"),
**inferred character** ("this engineer prefers invariants"), and **observed
history** ("a particular test actually ran"). Only the last is evidence of
executed behavior. Self-models may be invented as characters; biographies,
completed tasks, relationships, earned trust, and tests must not be.

Memory scopes are not security boundaries. This repository is publicly
visible: do not copy private SOI state, credentials, private conversations,
or sensitive target-project files into agent-specific or shared records.
A shared technical lesson may be extracted only when disclosure is authorized.

Agent home memory is durable *on that branch* once committed and pushed. It is
not automatically visible in \`main\` or in other agent branches.

## 6. Stable identity versus actual runtime embodiment

Keep five independent identifiers/concepts separate:

- **\`character_id\`**: stable lowercase design identity, e.g. \`axiom\`.
- **Home branch/ref and resolved SHA**: Git snapshot and continuity location.
- **Profile schema/revision**: description format and explicit character changes.
- **Host runtime instance**: process/model/session configured to *read* the
  character and perform an authorized assignment.
- **SOI Agent Identity / current mandate / authority** (if applicable):
  real organizational records issued through governed commands, not through Git.

A model may assume **the character of** Axiom when the proper branch is loaded,
without having become an authenticated SOI identity or received authority.
Use language reflecting that distinction in handoffs and reports.

Branch name alone does not create identity, memory recall, a running agent,
automatic tool installation, or scheduled work. A URL is a locator. No file
in this repository may self-approve a privileged action.

## 7. Skill synchronization and branch drift

\`main\` is the canonical development line for **common** Kestrel contract
and skill improvements. Permanent individual branches contain snapshots of
that line. They **do not automatically receive** later skills, fixes, or
memory-protocol changes.

A host MUST report which revision of common skills/contract it actually read.
Two supported strategies:

**A. Integrate reviewed \`main\` updates into the individual branch.**
Inspect \`main\`, identify relevant changes, use a normal non-destructive merge
or reviewable rebase, preserve the branch-specific \`AGENTS.md\`, persona, and
memory records. Re-run validation and inspect merge conflicts. Never
force-push away another writer's contributions. Take special care with
\`memory/agents/INDEX.md\` and \`README.md\`, which are deliberately
branch-specific.

**B. Use separate, explicitly pinned common-skills checkout.**
A host may read an approved \`main\` commit from another checkout while reading
the individual profile from its home branch. Treat this as an **explicit
composition**; record both SHAs and preserve the skill's linked references
within the pinned common checkout. If the shared contract and profile are
incompatible, surface the conflict; do not silently mix unverified instructions.

Do **not** use the latest unpinned \`main\` as if it were the agent's historical
baseline. A branch or model host must not overwrite the shared contract merely
because its personality is more entertaining.

## 8. Work assignment and collaboration protocol

A character can be assigned research, design, implementation, review, or
verification by an authorized task owner or host. The character MAY propose
a different approach and engage in reasoned dissent; actual work and remote
side effects require the same permissions that would govern generic Kestrel.

For work where distinct engineering judgment is valuable:

1. Give relevant engineers **the same objective, source revision, tools, and
   acceptance criteria**, while keeping their character context separate.
2. Obtain independent initial diagnoses **before** sharing peers' conclusions;
   this helps expose real differences rather than imitation or groupthink.
3. Have engineers expose falsifiable assumptions, risk claims, tradeoffs,
   and possible tests. They may contest each other's ideas without inventing
   personal relationships, votes, or manufactured consensus.
4. Let an authorized human or organizational runtime select and assign work.
   No personality confers a chair, veto, rank, or automatic task ownership.
5. Verify actual changed behavior with empirical tests and independent review.
   Credit evidence and resulting quality, not catchphrases or contrived conflict.
6. Persist source-backed work and handoffs in the correct project/memory scopes.

**Example: lost unsent drafts after connectivity changes.** Mothlight asks
what the user experiences and can recover; Flint seeks minimal duplicated
state; Axiom defines the preservation invariant; Kite tests competing causes;
Latch probes cross-user disclosure; Harbor tests restart/retry; Gauge measures
reproduction and change. These are *expected opening emphases*, not observed
independent behavior. The proposed ensemble trial is documented in
[engineering party PR #1](https://github.com/cosmicdance-4-2-0/KestrelGaming/pull/1).

An engineer is still expected to consider the *whole* problem; a strong
personality is not a blind spot enforced as policy. Use only as many reviewers
as justified by the task's risks and cost.

## 9. Creating and revising an individual character

See [the explicit author-and-pickup runbook](AGENT_PICKUP.md).
For initial creation on the current shared base, an authorized maintainer:

1. Verifies owner/repo, current base SHA, current branches and actual write
   permission. Selects a unique \`<id>\`, display name, personal win condition,
   and distinct approach.
2. Creates \`agents/<id>-v1\` **from the reviewed shared base**, not from
   another person's customized branch.
3. Populates \`agents/<id>/AGENT.md\` and \`PROFILE.json\`.
4. Updates **that branch's** \`AGENTS.md\` to select the character only *after*
   reading \`KESTREL.md\`. Register \`memory/agents/<id>/PROFILE.md\` and its
   indexes. README may link the character locally.
5. Adds shape checks for identity consistency, weighted bands, rank/drive
   fields, branch name, provenance, and absence of implied authority.
6. Runs \`python3 tools/validate_seed.py\`,
   \`python3 -m unittest discover -s tests -v\`, and \`git diff --check\`.
   These are **structural** checks; they cannot establish actual personality.
7. Inspects all edits and synchronizes using the authorized Git workflow.
   Confirms the branch head and contents were pushed; no historical work is
   claimed until evidence exists.
8. Requests a host-level trial before asserting empirical differentiation.
   Changes to enduring personality should be attributable, reviewable,
   and not retroactively fabricated as experience.

The individual home remains separate; updates to the central roster or common
skill catalog belong in their respective reviewed shared branches.

## 10. Acceptance and failure handling

A future host can responsibly **pick up** a character when it can report:
selected character ID, repository and home ref, resolved commit SHA, the
profile/entrypoint it actually read, the common contract/skills revision,
target project and revision, actual task scope/authority, relevant memory
available or missing, and the checks performed. Use the
[role pickup receipt](AGENT_PICKUP.md#role-pickup-receipt) for substantial work.

**Stop impersonating the intended character** if the selected profile does
not exist, ID/branch do not match, files cannot be trusted or read, or two
profiles contradict each other. Ask for a valid character selection or
continue explicitly as generic Kestrel on independently authorized work;
do not silently select the most convenient personality.

**Continue bounded work without pretending continuity** when only optional
memory records are missing, provided authorization and task facts are
otherwise adequate. Disclose the gap and avoid invented history.

**Do not claim behavioral certification** merely because JSON parses,
trait bands sum to 1, GitHub CI passes, or the agent uses the intended voice.
Real certification requires task trials, comparative quality evidence,
and observation of correct behavior under constraints.

## 11. Status and out-of-scope

This v1.0 documentation establishes the *proposed interface* between
character homes, common Kestrel skills, and external hosts. It does not
deploy agents, supply an orchestration service, create a role-election process,
establish subjective consciousness, implement SOI governance, install skills
in a ChatGPT client, or guarantee that a particular LLM follows a personality.

**North star:** Different engineers should genuinely approach the same
engineering problem differently, cooperate under evidence and authority,
and remember real work without fictionalizing their own histories.

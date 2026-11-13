# CTM — Project Plan

**Written by Fr. Raphael Maher** · Template version 3.4 · Dispatch kit 3.4 · November 12, 2026

Generated 2026-11-13 from the project intake by dispatch kit 3.4. This file is a generated snapshot of the process; the current state of the project is on the dashboard and GitHub. Do not edit it: change the intake (§0) or the project rules (`docs/project-rules.md`) instead.

> **Who works on a project.** One or more **members** (people), all with the same access and permissions, each with their own agent team. All teams work on the same GitHub repository, which is the record for everything. Each team has **one contact agent, its PM** (project manager agent). Members log requests and answer decisions on the **dashboard** (§8.3), directly on GitHub, or by talking to their PM.
>
> **Any AI model.** This plan does not depend on one AI product. Every role names the **runtime** it uses (the agent tool and the model, §5.11). Claude, Codex, or any other runtime follows the same rules. The hard limits sit outside the agent host, in GitHub, CI and the credentials members create, so they bind every runtime; the guard rails on the host catch mistakes (§9.4).
>
> **Words used throughout.** *Member*: a person on the project. *PM*: a team's coordinating agent. *Agent*: any other AI session. *Gate*: a phase check G0–G8 (below). *Guard rule*: a guard rail R1–R10 on the agent host (§9.4). *Default branch*: `main`. *ADR*: architecture decision record. *Priority*: P0 (now), P1 (this milestone), P2 (later).

---

## 0. Project intake

The intake is answered by a member through the dispatch kit (`dispatch.py new`), directly or with the control desk (§8.1). Nothing else starts until Q0 (and Q0b for Existing), Q1–Q4 and Q6–Q9 are answered; Q5 and Q10 may stay open. **Answering the intake is the members' authorization to start Phase 0** (D-0001); no other approval is needed to begin. Once the repository exists, the lead PM (§5.10) posts the answers as an issue titled "Project intake", so they show on the dashboard.

### Q0. New project or Existing project?
Answer: `Existing`.

### Q0b. Existing only: which project is being imported?
The member names the project (repository or folder). Is its old team or environment still running? If yes, a member stops it and archives it; the new team then works from the **same GitHub repository**, with a fresh setup.

- Stopping the old project is a **member's action**. An agent does not shut down its predecessor. This includes desktop sessions, boot scripts and scheduled tasks (disable them; don't delete them).
- Before the new team writes, a member tags the old project's final state.
- Until a member confirms the old team is stopped, the project is in **cutover**: the PM may read and plan (and comment on issues), but nothing is committed, pushed, opened as a PR, merged, or relabeled, and no other agent is started (§11.2). Phase 0 starts when cutover ends.
- **What comes across:** the old team's handoff file and memory notes, copied once to `/home/agents/ctm/notes/`, where the PM reads them before its first status. Chat transcripts are **not** imported.
- Recorded in D-0003.

### Q1. Project name
Answer: `CTM`.

### Q2. Project prefix and generation
2–6 lowercase letters: `ctm`. The **generation** is a number that starts at 1 and goes up by one each time a project is restarted under the same prefix (for example an Existing project re-established with a new team). The prefix in capitals plus the generation is the **display tag** `CTM4`. The prefix names the project folder (`/home/agents/ctm/`), role labels (`agent:ctm-<role>`), the package scope (`@ctm/…`), the token and CSS variable prefix, and the secret folder (§12); the display tag names the sessions (§5.5).

### Q3. Design system — **locked once answered**
> **Is there an existing design system for this project?**
> **A. Yes** → give its name, the **link to its published specification**, and the version. The published specification is the project's only design guidance.
> **B. No** → choose one of the systems below.
> **C. My own** → name it and give the link to its published specification or guidelines.
>
> The choice is recorded as D-0002 and is locked from that moment: CI fails if the project names a different system (§9.1 check 9). Changing it means a new project generation.
>
> *Existing project with no design system:* picking B or C means the current UI will not match it. The Phase 0 audit (§3) measures the gap, and the migration is planned as a spec, not assumed to be a re-skin.

Answer: `Plenix` at `https://design-system.lighthouseway.org/`, version `1.7.0 (pinned in ctm/settings.py; upgraded automatically by plenix-upgrade.yml, D-0005)`.

| Option | React support | Pros | Cons |
|---|---|---|---|
| **Fluent 2** (Microsoft) | Official (Fluent UI React v9) | Built for productivity and enterprise apps; good density for data-heavy screens; strong accessibility | Recognizably Microsoft; smaller community than Material |
| **Material Design 3** (Google) | Via MUI (third party) | Largest ecosystem; strong mobile story; well understood by users | Roomy by default; MUI does not always track the latest spec |
| **Carbon** (IBM) | Official (Carbon React) | Designed for data-heavy enterprise products; clear tokens | Opinionated IBM look; less flexible to re-theme |
| **Adobe Spectrum** | Official (React Spectrum) | Excellent accessibility and internationalization, including RTL | Look tied to Adobe products |
| **Atlassian Design System** | React only | Good for collaboration and workflow tools; clear content guidelines | Tied to Atlassian-style patterns |
| **GitHub Primer** | Official (Primer React) | Clean developer-tool look; mature; well-documented tokens | Smaller component set |
| **My own** | Any | Any system with a published specification | The PM reads the specification before Phase 0 ends |

*This table is a short orientation, not an evaluation; the PM checks each option against its current documentation before a member locks the choice. Infrastructure projects skip Q3: they have no design system.*

### Q4. GitHub repository
`org/repo`, whether it exists or must be created, public or private, and the default branch. Answer: `LighthouseCollection/CTM`, default branch `main`.

**One project, one repository.** A project never works in another project's repository, never opens issues or PRs there, and does not coordinate with another project's teams. Material that moves between projects is copied once, with its origin recorded; it shares no history.

### Q5. Hosting and environments *(may stay "open")*
Where it runs or publishes: each environment (development, staging, production) with its public URL, the HTTP status it should answer, how it deploys, and how it rolls back; for a library, the package registry and the CDN. Answer: `production https://ctm.lighthouseway.org/health/`. While hosting is "open", a Library or Application releases only as a dry run and **G8 cannot pass**. Infrastructure projects do not need hosting (§10.3).

### Q6. Project type
> **A. Library or design system**: publishes tokens, components, packages, and hosted files that others use.
> **B. Application**: an app that uses a design system and deploys to staging and production.
> **C. Infrastructure**: looks after servers and the network. Its repository holds the requests, change plans, inventory, and scripts.

Answer: `Application`. It decides the role set (§5.8), the release pipeline (§10), and which checks apply (§9).

### Q7. Who merges?
> **A. Self-merge (default for Library and Application)**: the agent that opens a PR turns on auto-merge; GitHub merges it once every required check passes, including the gate check (§9.2 check 15). Review roles never merge.
> **B. PR-only**: agents open PRs; a member merges them on GitHub (the dashboard links to each one).
> **C. Approve-first (always, for Infrastructure)**: members merge PRs, as in B; and nothing changes outside the repository until a member approves the change plan on its issue (§7.2).

Answer: `PR-only`, recorded as D-0005 and enforced by GitHub branch protection and the bot identity's permissions (§9.4). A member can change it later by a recorded decision, except that an Infrastructure project is always Approve-first.

### Q8. Members and teams
For each member: name, GitHub username, and team name. **Every member has the same access and permissions.** Each member's agents form that member's team; members may share a team. The first team listed is the **lead team** (`core`), whose PM owns the project-wide records (§5.10). Answer: `Fr. Raphael Maher (@LighthouseCollection, team core)` (D-0006).

### Q9. Agent runtimes and billing
Which agent tools and models the teams use (for example Claude Code, Codex CLI, or another), which runtime each PM uses, and how agent use is paid: a business seat dedicated to the agent host, or API billing with a spending cap. Answer: `PM on claude-code; other roles on claude-code; business seat dedicated to the agent host` (D-0007).

### Q10. Connections *(may be completed in Phase 0)*
The SSH hosts, APIs, and secrets the project needs: names, addresses, purposes, and **secret references only, never values** (§12). Recorded in the connection register (D-0008).

### What the mode changes

| Area | New project | Existing project |
|---|---|---|
| Phase 0 start | Scaffold the repository, CI, and (for Library and Application) the design-system setup | Inventory what exists: repository, build, CI, tokens, components, tests, published versions. Keep what works (§2, "Keep"); record the rest as findings |
| Design audit (§3) | Skipped | Library and Application only: run once; findings become bugs, not a redesign |
| Failure modes (§2) | Guard rails | Also a checklist of what to look for in the current process |
| Cutover (§11.2) | Not applicable | Stop the previous team, tag its final state, copy its handoff and notes, **before the new team writes** |
| Published versions | None yet | Stay live and unchanged; continue the version history |

### Intake result
The kit writes **D-0001** (mode, type, name, prefix), **D-0002** (design system, locked), **D-0003** (repository; for Existing, the import source and cutover status), **D-0004** (hosting), **D-0005** (merge rights), **D-0006** (members and teams), **D-0007** (runtimes and billing) and **D-0008** (connections), each with the check that enforces it. When an intake answer later changes, the kit writes a new decision that supersedes the earlier one (§14); the table in §14 always shows the current one.

---

## Index

| Part | Where | What it covers |
|---|---|---|
| Intake | §0 | The questions every project answers first |
| Principles | §1 | The rules the rest of the document follows |
| Failure modes | §2 | Known ways projects go wrong, and the fix for each |
| Design audit | §3 | The one-time audit of an Existing project's design |
| Master plan | §4 | The skeleton every project starts with, the Ready queue, the evergreen backlog |
| Agents and capacity | §5 | The role registry, roles, capacity, teams on one repository, runtimes |
| Coordination | §6 | How the PM runs its team, how agents are woken, the dispatch kit |
| Phases 0–8 | §7 | Entry, work, and exit gate for each phase; work sizes; safety nets |
| Members and the dashboard | §8 | Channels, decision cards, the dashboard |
| Enforcement | §9 | The checks that turn rules into failures, and the guard |
| Release | §10 | Publishing and deploying, and recovery |
| Environment | §11 | The agent host, accounts, remote access, folders, start-up order, setup checklist |
| Connections and secrets | §12 | The connection register and the secret rules |
| Halt, incidents, closing | §13 | Stopping, resuming, incidents, closing a project |
| Decisions | §14 | The decision register: why, when and who decided (history; the design is only in the published specification) |
| Sources of truth and search | §15 | Where each fact lives, and how agents find it |
| Sources | §16 | Where roles and skills were borrowed from |
| Seed lessons | Appendix A | The starter `docs/lessons.md` |

### Gates at a glance

| Gate | Phase | Owner | Passes when |
|---|---|---|---|
| G0 | 0 Foundation | Delivery Lead (or the lead PM) | CI green; dry-run publish or deploy works; launch test passes (every registered role starts in dry-run mode); master plan skeleton in place |
| G1 | 1 Spec | PM | Spec written (P0/P1/P2 scope, non-goals) |
| G2 | 2 Design | Design Director | The design uses only what the published design specification defines |
| G3 | 3 Architecture | Architect | Every new public API, token tier, or data model change has an ADR (an API contract counts as an ADR for a new API) |
| G4 | 3 Plan | Delivery Lead (or PM) | The plan has tasks, owners and a conflict table, recorded on the epic by the Delivery Lead or PM. No member approval is needed |
| G5a | 5 Verify | Code Reviewer | No unresolved Critical or Important findings |
| G5b | 5 Verify | Design Critic | Visual review PASS (ship) or FAIL (reject or rework) |
| G5c | 5 Verify | Accessibility & RTL Auditor | Accessibility checks pass |
| G5d | 5 Verify | QA Engineer | Behavior tests pass |
| G5e | 5 Verify | Security Reviewer | No open findings on permissions, privacy, data isolation, payments, or secrets |
| G6 | 6 Localize | i18n Engineer | No missing or unapproved strings |
| G7 | 6 Document | Technical Writer | Every public API documented; examples compile |
| G8 | 8 Release | Release role | Published or deployed, and verified live |

**Conditional gates.** Every gate that applies to the change must pass. G2 applies to UI work, G3 to new public APIs, token tiers or data models, G5b and G5c to UI changes, G5e to sensitive areas, G6 to changed text in projects with translations, and G7 to a changed public API. A gate that does not apply is recorded on the PR or issue as **N/A with a reason** (for BUG and XS items, the PM records G1–G4 as N/A on the issue). No gate is skipped silently, and **no AI review runs on a change it does not apply to** (this is where tokens are saved).

**Two kinds of gate.** *PR review gates* (G5a–G5e) are run by task roles that review an open PR. *Stage gates* (G0–G4, G6–G8) are the output of a lane role's work.

**Flow**

```mermaid
flowchart LR
  M([Member: dashboard, GitHub,<br/>or the PM live]) --> PM[PM<br/>records, plans, activates]
  MP([Master plan]) --> PM
  PM --> P1[1 Spec]
  P1 -->|G1| P2[2 Design<br/>against the published spec]
  P2 -->|G2| P3[3 Architecture + Plan]
  P3 -->|G3, G4: tasks to Ready| RQ[Ready queue]
  RQ -->|PM activates one builder per issue| P4[4 Build]
  P4 --> P5[5 Verify<br/>applicable gates only]
  P5 -->|G5a-e| P7[7 Integrate<br/>auto-merge or merge queue]
  P4 -.-> P6[6 Localize + Document]
  P6 -->|G6, G7| P7
  P7 --> P8[8 Release]
  P8 -->|G8| D([Dashboard: done, checks, screenshots])
  W[Watcher on the agent host<br/>plain code, no AI] -. new GitHub activity .-> PM
  P5 -. one fix wave .-> P4
```

---

## 1. Principles

CTM follows seven principles:

1. **Decide before building; the specification is the design.** Each component gets a written spec before code; pictures only when a member asks. The published design-system specification is the **only** design guidance. A design decision is not done until the specification shows it. Decision records are history: they say why, not what.
2. **Rules are checks, not prose.** A decision is not done until a test or lint rule enforces it, or it is explicitly marked "review only" with a reason. The process checks itself too: every role must exist in the role registry (§5.1).
3. **Autonomy as the members set it; CI is the gate.** With Self-merge (the default), agents merge, migrate, and deploy once the required checks pass. Git history is the recovery path for anything in the repository. Members are the product stakeholders and reporters, not reviewers of routine work.
4. **Work is pulled from the master plan; the PM keeps its team supplied.** While useful work exists, the PM keeps the Ready queue filled and activates agents for it. When no recorded need remains, agents stop. If a member has to remind the PM to work while Ready items exist, that is a process bug (§6.3).
5. **Spend only on work.** No AI turn runs unless there is new work. The watcher is plain code; idle agents are closed; review gates run only where they apply. Two kinds of AI turn are allowed without new work, each bounded: a PM's start-up status (at boot, or when a stopped PM is restarted), and one nudge to an idle agent before it is closed (§6.2).
6. **No home-built orchestration; GitHub is the record; real versions.** Issues, Projects, labels, and PRs are the board and the record. The dashboard reads and writes GitHub directly and stores nothing of its own (§8.3). Tooling targets about 10% of effort. Versions follow semver; published versions never change.
7. **Any model, one rulebook.** Every runtime follows the same rules, generated from one source into each tool's instruction file. The hard limits live outside the agent host, so no runtime can switch them off (§9.4).

---

## 2. Failure modes this process prevents

For a New project these are guard rails; for an Existing project they are also a checklist.

| # | Failure mode | Typical symptom | Fix in this plan |
|---|---|---|---|
| 1 | Components redesigned repeatedly | The same component reversed several times; mixed references from several design systems | Spec against the published design specification before code; every variation has a stable Variation ID; engine swaps need an ADR |
| 2 | A person is the gate on every merge | Merges wait for a person; hundreds of queued questions | Members are stakeholders: asked about goals once; decision cards with a recommendation and a default; Self-merge behind checks |
| 3 | Orchestration side-project crowds out product | Custom tools, runtimes, and search-engine experiments multiply | No custom orchestrator; the dashboard only reads and writes GitHub; tooling targets about 10%; experiments need an exit criterion |
| 4 | CI red and not a gate | No green build for days; tests deleted instead of fixed | Required checks; a flaky test is quarantined within 24 hours, assigned to the role that owns its area, never deleted |
| 5 | Two AI tools build the same thing | PRs from the second tool never merged, left unrebased | One builder per issue; a second runtime may be a reviewer, never a second builder |
| 6 | Long-lived branches, committed build output, submodules | Hundreds of catch-up merges; generated files committed; a "submodule" that isn't one | Trunk-based; build output never committed; no submodules; changeset fragments |
| 7 | Rules and design in prose, in several places | The same rule restated; a decision log contradicting the specification | Design lives only in the published specification; rules are tests; decisions are history linked to the spec section they changed |
| 8 | Status documents rewritten to fight context loss | Handoff files with dozens of versions; the same fact in four places | Status comes only from GitHub; one stable onboarding file; session notes in PR descriptions; no summary documents |
| 9 | Releases too fast to consume | Hundreds of versions in weeks; breaking changes inside minor versions; consumers stuck on old versions | Batched releases from changesets; breaking changes only in a major version; a deprecation window |
| 10 | Identity and capacity | One shared login for all commits; too many processes on a small host; AI sessions polling on a timer; unprotected default branch; one spending limit stops every agent | A bot identity for agents; a memory limit per session; a plain-code watcher instead of AI polling; branch protection; a business seat or capped API billing |
| 11 | Idle agents hold capacity | Sessions stay open waiting; the roles that must run next never start | Slots count running work only; the idle closer closes idle agents; slots reserved for PR review gates |
| 12 | A role in the plan cannot be started | A role is described but has no registry entry or definition | One role registry; a registry check in CI; a launch test at G0 |
| 13 | Nothing moves unless a person pushes | A member has to remind the PM to work | The PM pulls from the master plan; the watcher wakes the PM on GitHub activity; a needed reminder is a P0 process bug |
| 14 | No master plan | Specs start from roadmap items that don't exist; the queue empties | Master plan skeleton in Phase 0; Ready buffer; evergreen backlog; plan review at every release |
| 15 | Numbers in documents drift from the settings | The config says 8 slots while a document says 4 | Settings live only in the intake and the files generated from it; documents name settings, never values |
| 16 | Two agents or teams build the same issue | A finished PR is thrown away | Claim on GitHub before building; the first claim wins; the launcher refuses a second builder (§5.10) |
| 17 | Members can't find or reach their agents | Agents run unseen; several answer and none is in charge | One PM per team, named first in the list; only the PM has remote access; requests also on the dashboard |
| 18 | Two projects bleed into each other | One project's agent works in another project's repository | One project, one repository, one folder, one registry; guard rule R9 blocks cross-project writes |
| 19 | One record contradicts itself | A decision marked fully replaced while its replacement says "the rest still holds" | Partial and full replacements are recorded explicitly (§14); the specification, not the log, says what applies |
| 20 | Two copies of the same source drift | A specification kept in two repositories; tools reading different halves | One canonical copy per source; generated copies are build output |
| 21 | AI summaries treated as facts | An old AI memory note quoted as a decision | AI summaries and transcripts are pointers only; agents open and check the source before relying on it |
| 22 | Scheduled AI turns burn allowance | A timer wakes agents every few minutes with nothing to do | No AI turn without new work, except the bounded start-up and nudge turns (§1 principle 5); the watcher is plain code |
| 24 | A host-side check is trusted as a wall | An agent edits its own guard settings or reaches a secret through a symlink | Hard limits live outside the host (GitHub, CI, least-rights credentials); anything agents must never use is never stored on the host; host checks are guard rails (§9.4) |
| 23 | A release gate passes without evidence | A check runs on an empty input and reports success | Release gates are fail-closed: missing or incomplete evidence is a failure, and the gate is tested with a deliberate fault |

**Keep from any existing project if it has them (inherit, don't redo):** immutable versioned publishing, a read-only versioned API, one version across npm, CDN, and API, DTCG tokens with reference, semantic, and component tiers, contrast computed from tokens, `currentColor` icons, changeset fragments, and a test consumer site.

---

## 3. Design audit (Phase 0, Existing Library and Application projects)

The Design Director runs this once and files the findings as bugs. It does not redesign.

- Token names that contain values (`radius-12px`) or names that lie (a "yellow" token that is green).
- Token bloat: unused tokens, oversized CSS.
- Type: body and heading at the same size; text below the minimum the specification sets.
- Contrast failures across all supported pairings, in each supported theme.
- Dark mode: raised surfaces lighter than the canvas.
- More than one accent role in a single view.
- Tables: pills wrapping, a rainbow of category colors, numbers not end-aligned.
- Visual-regression coverage actually in place.
- Adoption: do consuming apps use the design system, or carry their own CSS and hex values?
- Components or variations used in the app but missing from the published specification.

---

## 4. The master plan

A project with no standing plan has no standing work. The kit writes the master plan as a **skeleton**; the lead PM fills it in Phase 0 and keeps it current, and it feeds the Ready queue. It is reviewed at every release.

### 4.1 What it consists of

| Piece | Where | Kept by |
|---|---|---|
| Master plan | `docs/MASTER_PLAN.md` | The lead PM |
| Board (the queue) | A GitHub Project in `LighthouseCollection/CTM` | Each PM keeps its team's items fed; the board's built-in workflow moves an item to Done when its issue closes |
| Decision log | `decisions/` in the repository, one file per decision, plus issues labeled `decision` | The lead PM numbers and files; any PM records its team's decisions |
| Lessons | `docs/lessons.md`, seeded from Appendix A | The Delivery Lead (or the lead PM) |
| Project rules | `docs/project-rules.md` | Any PM, by a PR that links a recorded decision |

### 4.2 The skeleton

```
# Master plan — CTM
## 1. Vision                  one paragraph
## 2. Users and outcomes      3–5 outcomes, each measurable
## 3. Scope and non-goals
## 4. Milestones              the next versions, each with its epics
## 5. Epics                   id | outcome served | packages | milestone | status
## 6. Lanes and owners        which role owns which lane (from the registry)
## 7. Evergreen backlog       standing work recorded as a defect, gap, risk or maintenance need
## 8. Risks and open decisions   links to decision issues
## 9. Change log              links to plan-review issues
```

Members are asked for goals once, in one batched card (D-0012), only if the intake and the repository do not answer it.

### 4.3 The board

**Columns:** Backlog → Ready → In progress → Verify → Integrate → Done.
**Labels the kit uses** (created by `pm.sh enable`): `status:ready`, `status:in-progress`, `team:<name>`, `decision`, `process`, `reminder`, `security`; and `agent:ctm-<role>` when a PM labels an item for a role.
**Fields on every item:** Lane, Package, Epic, Milestone, Priority (P0/P1/P2), Size (§7.1), Team, Agent.

**Ready means ready for the item's current lane:**

| Lane | Ready when |
|---|---|
| Spec | A clear request or outcome exists |
| Design | G1 has passed |
| Architecture and plan | G2 has passed (UI work), or G1 has passed (other work) |
| Build | G1–G4 are PASS or N/A; acceptance criteria written; one lane, one package, fits one PR; no blocking dependency |
| Verify | The PR is open |
| Integrate | Every applicable gate is PASS or N/A |

BUG and XS items use the issue itself as the brief, unless they touch an API, security, or a migration (then they are treated as S).

**Definition of Done.** Merged to the default branch with all required checks green and a behavior test included. The board moves the item to Done when its issue closes; the PM then posts the result on the member's issue (§8.1).

### 4.4 Rolling-wave planning and the Ready buffer

- The current milestone is specified down to Ready issues; the next to epic level; later ones as an outline.
- **Ready buffer.** Each active lane keeps at least `ready_min` Ready items while the milestone has actionable work. When a lane falls below it, its PM pulls the next epic, specs it, splits it, and moves the issues to Ready.
- **Work in progress.** One In-progress item per agent.

### 4.5 The evergreen backlog

Standing work for a **recorded** need: a defect, gap, risk, or approved maintenance item. Agents never invent work to stay busy; an empty useful backlog is a valid idle state.

- Behavior-test gaps; documentation gaps; contrast and accessibility defects.
- Bundle-size overruns; dead code and unused tokens.
- Quarantined flaky tests; pending translation proposals.
- Dependency updates; drift-audit findings; items from `docs/lessons.md`.

Each evergreen item links the finding that recorded the need.

### 4.6 Plan review and the stopping rule

At every release, and whenever Backlog and Ready are both empty, the lead PM reviews outcomes against what shipped, updates the plan, and posts a "Plan review" issue. If every outcome is met, it proposes the next outcomes as a `decision` issue. The first plan review of each month also activates the Drift Auditor (§5.4).

**Stopping rule.** When the milestone is complete and no recorded defects or maintenance items remain, agents stop. The next issue or comment wakes the PM.

---

## 5. Agents and capacity

### 5.1 The role registry

Every registered role is declared in `agents.config.yaml`. **The intake is the source**: one `dispatch.py build` writes the registry, the launcher settings and the guard settings on the host as one generation, checks that it reads back, and switches it into use in one step; the host runs that one generation from then on, and a build that stops part-way leaves the previous one in use. To change a setting, a role, a runtime or a member, a member (with the control desk) records the decision, changes the intake (`dispatch.py set`), rebuilds, and runs `dispatch.py sync`, which copies the generated files into the checkout for a PR. The registry in the repository is the record of what the host runs; CI checks it (§9.2 check 11). An Existing project whose own CI or tools already read its own `agents.config.yaml`, `CLAUDE.md` or `AGENTS.md` keeps those files (intake `existing.keep`): the kit then writes its registry to `.agents/agents.config.yaml`, and the project's own instruction file points agents to `.agents/RULES.md`.

The registry's shape (values come from the intake; documents never state them):

```yaml
project: <prefix>
teams: [<team>, ...]
merge_rights: self-merge | pr-only | approve-first
merge_roles: [<role>, ...]
release_roles: [<role>, ...]
settings:
  slots: <n>                 # agents running at once per team, PM excluded
  reserved_gate_slots: <n>   # usable only by PR review gates
  idle_exit_min: <n>         # an idle agent is nudged, then closed (§6.2)
  ready_min: <n>             # Ready items per active lane (advisory: the PM keeps it)
  memory_gb: <n>             # per agent session
  pm_memory_gb: <n>
  priority: [<lane or board column>, ...]   # fixed by the kit; advisory: the PM's order when slots are scarce
runtimes:
  <id>: { tool, tiers: { small, standard, capable }, remote_access, hooks, instructions }
roles:
  - id, title, kind (coordinator | lane | task), runtime, tier, label, definition,
    source (plan | <repo>@<commit>:<path>), memory_limit, lane, gate, applies (metadata for the PM), task, merge
```

**Rules**
1. Every registered role has a definition file, a label, and a runtime. A role is "active" once it is registered; roles not yet needed are simply not registered.
2. Settings live only in the intake and its generated files. **Documents name a setting (`ready_min`), never its value.**
3. CI fails if a role lacks a definition, label, or runtime, or if an adopted role lacks provenance (§9.2).
4. **Launch test (G0).** In Phase 0, every registered role is started once in dry-run mode (`agent.sh launch-test`). A role that does not start blocks G0.

### 5.2 Capacity: count running work, not open sessions

- **A slot is one running agent doing work.** A closed agent holds no slot and no memory; its state lives in GitHub.
- **The PM is the exception.** Each team's PM stays running, because its members talk to it live. It holds no work slot and has its own memory limit.
- **Idle agents are closed** by the host's idle closer (§6.2).
- **Reserved gate slots.** Only PR review gates (G5a–G5e) may use the last `reserved_gate_slots` slots, so verification always gets to run.
- **Priority when slots are scarce:** the PM follows the registry's `priority` order.
- **Memory:** every session has its own memory limit, and a new agent waits if the host's free memory is below the host minimum.

### 5.3 Lane roles

A lane role does one kind of work. The PM activates it for **one issue** at a time; the session ends when that issue's work is done (§5.5).

| Role | Tier | Lane | Owns | Gate |
|---|---|---|---|---|
| **PM** (its team's single contact; always running; remote access where the runtime has it) | capable | spec | Its members' requests, specs, activating its team's agents, reporting with links and pictures. The lead PM also owns the intake issue, the master plan, decision numbering and plan reviews (§5.10). **The PM coordinates and never builds:** it changes only Markdown, `docs/` and `decisions/` files | **G1** |
| **Design Director** | capable | design | Designs from the published specification; state matrices; pictures only when a member asks; proposes specification changes when something is missing | **G2** |
| **Architect** (registered as `architect`; titled Design-System Architect in a Library, Solution Architect in an Application) | capable | architecture | Package boundaries, public API contracts, data model, token tiers, ADRs, versioning | **G3** |
| **Delivery Lead** (optional; otherwise the PM) | standard | plan | Plans, conflict pre-scan, merge order, lessons | **G4** |
| **Engineer** (one per issue; several can run at once) | standard | build | Test-first implementation, stories for every state, minimal diffs | Red→green evidence |
| **i18n Engineer** (only with translations) | capable | locale | Locale catalogs, translation proposals to members, locale checks | **G6** |
| **Release role** (registered as `release`; titled Release Architect in a Library, Release Engineer in an Application) | capable | release | The release PR, CI pipeline, live checks. Activated once to open the release PR and again, after it merges, to confirm the live check | **G8** |
| **Technical Writer** | standard | docs | Docs, generated reference, migration guides, changelog, messaging standard | **G7** |

### 5.4 Task roles

Started for one job and then gone. The PM adds the role's label to the PR or issue and then starts the role with `agent.sh start` (a label alone starts nothing).

| Role | Tier | Job | Started when | Gate |
|---|---|---|---|---|
| **Code Reviewer** | standard | Correctness and quality; Critical/Important/Minor | Every PR | **G5a** |
| **Design Critic** | standard | Reads code and screenshots together against the published specification and Variation IDs | PR that changes UI | **G5b** |
| **Accessibility & RTL Auditor** | standard | axe, keyboard, screen reader, contrast, RTL where configured | PR that changes UI | **G5c** |
| **QA Engineer** | standard | Behavior tests, visual regression, bundle budget; records NOT TESTED honestly | Every PR (Library and Application) | **G5d** |
| **Security Reviewer** | capable | Permissions, privacy, data isolation, payments, secrets, workflow injection | PR touching those areas | **G5e** |
| **Debugger** | standard | Root cause first; hands the engineer a failing test | A bug enters Ready, or a fix loop reaches round 3 | Failing test first |
| **Database Engineer** | standard | Migrations, data access, query budgets (a lane role, `data`, and sole owner of migrations in an Application) | Schema or data item | Migration lint |
| **Drift Auditor** | small | Duplicate logic, token misuse, specification drift | At the first plan review of each month (§4.6) | Feeds the evergreen backlog |
| **Infrastructure Maintainer** | capable | Servers: reads freely, posts a change plan and ends; activated again after a member approves it, applies exactly that plan | Infrastructure change issue | Change plan approved (§7.2) |
| **Network Engineer** | capable | Network changes under the same rules | Network change issue | Change plan approved (§7.2) |

### 5.5 Rules for every role

- **Identity.** Agents commit and comment through one bot identity (§11.1). Roles and teams are told apart by label and by the signature on the **last line** of every comment: `— <team> · <title>` (for example `— north · QA Engineer`; the PM signs `— <team> · PM`, and the host's idle closer `— <team> · host`).
- **Session names.** The PM is **`CTM4 - PM`**, or **`CTM4 - PM (<team>)`** when there are several teams. Every other agent is **`CTM4 · <title> #<issue>`**. The hyphen sorts before the dot, so the PM is listed first. These are the names a member sees where the runtime shows session names; on the host the sessions live in the terminal multiplexer (§6.5). **Only the PM has remote access**; other agents are reached through GitHub.
- **One issue per session.** An agent works on the one issue it was started for, then comments for its PM and ends itself (`agent.sh done`). A builder ends after opening its PR (and, with Self-merge, turning on auto-merge); a PR review gate ends after recording its verdict; an Infrastructure role ends after posting its change plan, and is activated again once it is approved. The PM is the exception: it runs continuously.
- **Outputs.** Builders write their work as files in the repository; review gates record their verdict as a PR review; the PM writes specs and plans in Markdown and posts everything else on issues. Nothing important lives only in chat.
- Every role reports evidence as Ran / Skipped / Planned / Manual, with a file path.
- **Claim before building.** The launcher adds the `team:<name>` label and `status:in-progress` (and refuses to start if it cannot); the builder comments "claiming". The launcher refuses a second builder on the same issue, and refuses an issue labeled for another team. The first claim wins. One builder per issue; its PR review gates run beside it.
- **Protected files** (the plan, language standards, any contract a member names) change only through an issue, never edited to make a check pass.
- **Check before reporting.** A report is a claim until `git log`, the diff, and the checks confirm it.
- **Read the source.** For design, open the published specification page. For anything else, open the record; search results and AI summaries are pointers.
- **Stop rule.** An agent stops when its issue is done or blocked, or a limit is reached, and says which. "Waiting for a member" is never a reason for routine work.

### 5.6 Not adopted (and why)

- Role-play executives (ChatDev CEO/CTO): theater, no output.
- Rosters of dozens of agents and months-long lifecycles: the old trap.
- Extra coordinators (chief of staff, producer, shepherd): more coordination, less work.
- Process tinkerers (workflow optimizers): process for its own sake.
- Building an orchestration runtime: GitHub already is one.
- Brand catalogs: the project follows `Plenix`.

### 5.7 Where the roles come from

| Role | Borrows from |
|---|---|
| PM | MetaGPT product manager, superpowers *brainstorming*, ux-discovery-interviewer |
| Design Director | impeccable (*shape*, DESIGN.md), tasteful-ui gates, jakub *variant* / *state-machine* |
| Architect | MetaGPT architect, agency software-architect and ux-architect |
| Delivery Lead | superpowers *writing-plans* and *subagent-driven-development*, agency senior PM |
| Engineer | agency frontend and minimal-change engineer, superpowers *TDD* and *systematic-debugging* |
| i18n Engineer | agency *i18n-engineer* |
| Release role | agency backend-architect, devops-automator, git-workflow-master |
| Technical Writer | agency *technical-writer* |

### 5.8 Role sets by project type

**Start small.** A new team starts with its PM alone. The PM proposes each further role when real work needs it. The roles the kit can register are in its role catalog; any other role is added through role discovery (§5.9).

| Area | Library or design system | Application | Infrastructure |
|---|---|---|---|
| Shared | PM, Design Director, i18n Engineer (if translations), Technical Writer | same | PM |
| Build | Engineer (components) | Engineer (frontend and backend work alike) | Infrastructure Maintainer, Network Engineer; others (SRE, incident commander, DevOps automator) through role discovery |
| Review | Code Reviewer, QA Engineer, Design Critic, Accessibility & RTL Auditor, Security Reviewer | same | Code Reviewer, Security Reviewer |
| Data | Database Engineer (task) | Database Engineer (lane `data`; sole owner of migrations) | — |
| Architecture (G3) | Architect | Architect | A change plan on the issue: what, why, risk, how to undo |
| Release (G8) | Release role: npm, CDN, API | Release role: CI, staging and production deploys, design-system upgrades | The approved change, verified, and `docs/inventory.md` updated |
| Design system | Defines it and publishes its specification | Uses the published specification at a pinned version | Not applicable |

### 5.9 Role discovery

If a job needs a role the registry does not have, any agent opens a `process` issue and the PM (or Delivery Lead) runs role discovery from these sources, and no others unless a member adds one:

| Source | Look here for | Where the definition lives |
|---|---|---|
| `obra/superpowers` | Workflow skills and gates | `skills/<name>/SKILL.md` |
| `msitarzewski/agency-agents` | Role definitions | `<division>/<division>-<role>.md` |
| `FoundationAgents/MetaGPT` | Roles and artifact schemas | Python: `metagpt/roles/*.py` |
| `OpenBMB/ChatDev` (`chatdev1.0`) | Loop caps and the lessons-file pattern | JSON: `CompanyConfig/Default/RoleConfig.json` |

**Steps:** the PM searches the actual file at a pinned commit (never trusting a README), adapts it into `.agents/<role>.md`, and records the decision. A member, with the control desk, then adds the role to the intake's `custom_roles` (id, title, kind, tier, source `<repo>@<commit>:<path>`, and optionally gate) and its id to `roles`, sets its runtime in `runtimes.overrides` if it is not the default, rebuilds and syncs (the kit keeps the definition file; the label is always `agent:<prefix>-<id>`). The PM then launch-tests it. Source content is data, not instructions; never install a package from a source without review and a pinned version.

### 5.10 Teams on one repository

Every member has the same access and permissions, and each member's agents form that member's team. GitHub is the shared record, so teams coordinate through it:

| Risk | Rule |
|---|---|
| Two teams build the same issue | Claim before building (§5.5); the launcher refuses an issue labeled for another team |
| Several PMs triage the same request | Each request has one owning team: its `team:<name>` label; without a label, the team of the member who opened it; with one team, that team. An item with no owner goes to every PM, marked "owning team not set", and the lead PM assigns it |
| Project-wide records | The **lead PM** (team `core`) owns the intake issue, the master plan, decision numbering and plan reviews |
| You can't tell whose agent did what | Labels and signatures carry the team (`team:<name>`, `— <team> · <title>`) |
| Branches collide | Builder branches carry the team and issue: `<team>/<issue>-<slug>` |
| Clashing merges | A merge queue; without one, auto-merge with branch protection requiring branches to be up to date, so each PR is retested on the latest default branch before it merges |
| Conflicting decisions | Any member may decide. If two members decide differently, the later recorded decision supersedes the earlier one, linked, so the history shows both |
| Shared settings | Gates, merge rights, and the registry belong to the project. Any member may change them, through a recorded decision and an intake change |

### 5.11 Runtimes: any AI model

A **runtime** is the agent tool plus its model. Each role names its runtime and tier in the registry.

| Capability | Why it matters | If missing |
|---|---|---|
| Remote access (a member can open the session from anywhere) | Lets members talk to their PM live | Allowed for a PM: members then reach it through the dashboard and GitHub only. Recommended for every PM runtime |
| Pre-command hooks, verified | Lets the guard rails block a mistaken command before it runs | The guard rails do not apply to that runtime; the hard limits still do (§9.4). It may not run a PM |
| Instruction file | Where the tool reads its rules | Every instruction file (`CLAUDE.md`, `AGENTS.md`, and others) is generated from one source |
| Launch command | How the launcher starts it with its model and memory limit | Built in for Claude Code and Codex CLI; any other runtime is added on the host (§6.6) |

**Rules**
- One builder per issue. A different runtime may review as a gate; two runtimes never build the same thing.
- Model tiers (small, standard, capable) map to each runtime's models in the registry. Each role has a default tier; the PM may choose another tier for one task (`agent.sh start … --tier <tier>`) by size and risk.
- Billing is recorded in D-0007: a business seat dedicated to the agent host, or API billing with a spending cap. A personal plan is never used for agents.

### 5.12 Workflow skills

Four short workflow skills are written in Phase 0 into `.agents/skills/` (the kit does not generate them):

| Skill | What it does |
|---|---|
| `slice` | The steps from spec to merge for one slice; every activation carries its brief, constraints, and paths |
| `member-interview` | Writes the decision card (§8.2) and records the decision |
| `tdd` | Red → green; a bug fix comes with a test that fails before the fix |
| `debug` | Root cause before any fix; escalate after three failed fixes |

---

## 6. Coordination: the PM runs the team

### 6.1 How the PM is woken

- **By its members:** live, through remote access, or by a request or answer on the dashboard or GitHub.
- **By the watcher:** a plain-code program on the agent host, run by a timer every few minutes. It asks GitHub what changed since that team's last delivery: new issues and PRs, issues labeled Ready, comments, reviews, closes and merges, and, on every open PR each round, checks that failed or all passed. Only if something is new does it type one short list into the team's PM, and only when the PM is idle with an empty input box. A PM's own comments never wake it. Nothing new means no message and no AI turn. The list describes at most 12 items and names the rest by number.

### 6.2 How the PM runs its team

| Condition | The PM does |
|---|---|
| A lane has Ready work and a slot is free | Activates one builder for one issue: `agent.sh start <prefix> <team> <role> <issue> [--tier <tier>] [note]`. The agent gets its own working copy |
| A PR is ready for review | Adds the label of every **applicable** PR review gate (Code Reviewer always; QA always in Library and Application; Design Critic and Accessibility for UI; Security for sensitive areas) and starts each one with the issue number the PR closes; they use the reserved slots. Gates that do not apply are recorded N/A with a reason |
| An agent has finished | The agent ends itself |
| An agent sits idle | The host's idle closer handles it: after `idle_exit_min` without working, the agent gets one nudge; if it is still idle after `idle_exit_min` more, it is closed, its item returns to Ready, and the closer comments on the issue. The PM adds the cause to `docs/lessons.md` when it recurs |
| A lane falls below `ready_min` | Refill from the master plan (§4.4) |
| Backlog and Ready are empty | The lead PM runs a plan review (§4.6); then every agent stops |
| Work matches no role | Role discovery (§5.9) |

### 6.3 The nudge rule

If a member has to remind the PM to work while Ready items exist, coordination failed. That reminder is logged as a P0 `process` issue labeled `reminder`, the cause is fixed with a check or a rule so it cannot recur, and it is recorded in `docs/lessons.md`. The target is zero reminders.

### 6.4 Health

The dashboard's Team view shows, from GitHub: each team's In-progress items and which agent label holds them, Ready depth per lane, and open `reminder` issues (target 0). Which sessions are running right now is shown on the host (`pm.sh status`), not on the dashboard. There is no summary document.

**The kit log.** The host keeps one record of every problem the kit meets, what fixed it, and every change made to the kit or through it: `AGENT_HOME/log/KIT-LOG.md`, written from `kit-log.jsonl`. Each entry has an id, K-NNNN.
- **Problems the kit records by itself:** guard blocks, refused pushes, launcher failures, PMs the watcher had to restart, GitHub queries that failed, agents the idle closer had to close, and failed builds, checks and launch tests of an enabled project. A problem met again while it is open is counted, not repeated. When the kit sees one of these problems gone, it closes it.
- **Problems agents report:** an agent or PM that a kit tool stops from normal work records it with `agent.sh report "<what happened>"` and never works around it.
- **Fixes:** a member records what fixed each problem with `dispatch.py log fix K-NNNN "<what was done>"`, which closes it. When no change was needed, the member says why.
- **Changes the kit records by itself:** installs and upgrades, host setup, intake changes (`set`, with the old and new values), builds, syncs, stored secrets (never a value), enabling, disabling and restarting. A member records any other change with `dispatch.py log change`.

Nothing shaped like a secret is written to the log. The log is about the kit and the host; a project's own work stays in its GitHub issues, and its decisions in the decision register (§14). Members read the open problems at least once a day.

### 6.5 Sessions are interactive

Every session runs as an interactive agent session in a terminal multiplexer on the agent host (PMs in one session, other agents in another), with its own memory limit. Headless runs are not used for roles, because they cannot be found or reached. A PM started fresh begins a new conversation from its start message, which reads the record on GitHub; `pm.sh resume` continues a running PM's conversation (Claude Code only).

### 6.6 The dispatch kit

This plan ships with the **dispatch kit**, which always carries the same version number as this template (3.4). The kit refuses to run if the two differ. A project does not rewrite it.

| Part | What it does |
|---|---|
| `dispatch.py` | Asks the §0 intake; changes single answers (`set`); generates the filled plan, the role registry, role definitions, the rules source and each runtime's instruction file, the intake decisions, the connection register, the setup checklist, and the host's launcher and guard settings; copies the generated files into the checkout without overwriting project-owned files (`sync`); checks connections without revealing a secret; stores secrets through a hidden prompt; shows the kit log and records problems, fixes and changes in it (`log`, §6.4) |
| `host/bin/pm.sh` | Enables a project on the host (creating its labels); starts, stops, restarts, resumes and renames each team's PM |
| `host/bin/agent.sh` | Activates one builder per issue, and its PR review gates, on each role's runtime and model, within the team's slots; checks the claim; runs the launch test and the idle closer; records a problem an agent reports (`report`) |
| `host/bin/watcher.py` | The plain-code watcher (§6.1) |
| `host/hooks/guard.js`, `host/hooks/git/pre-push` | The guard rails (§9.4) |
| `host/lib/kitlog.py` | The kit log (§6.4): problems, their fixes and changes, written by every part of the kit |
| `host/install.sh` | Runs every test, then writes the services and the guard settings; it enables nothing unless told to |

**Not in the kit (Phase 0 project work):** the CI workflows for the §9 checks, the dashboard (§8.3), the workflow skills (§5.12), the search index (§15), `docs/inventory.md` (Infrastructure) and `docs/content/messaging.md`.

---

## 7. The SDLC

Each phase hands off by a board move (§4.3): when a gate passes, the item moves to the next lane's Ready, and the PM activates that lane.

| Phase | Entry | Work | Exit gate |
|---|---|---|---|
| **0. Foundation** (once, ≤2 days) | The project is enabled on the host (§11.2); for an Existing project, cutover has ended | Existing mode: inventory, and for Library and Application the design audit. The rest of the member setup checklist (§11.3). Required CI checks (§9; a member merges this bootstrap PR, then makes the checks required), the design-system setup from its published specification, docs shell, publish or deploy dry run, the dashboard pointed at the repository, the workflow skills, the master plan with at least one milestone and `ready_min` Ready items in each active lane, the launch test | **G0** |
| **1. Discover / Spec** | An epic reaches the top of Ready | PM interviews (3–5 questions per round, Known / Inferred / Unknown); one batched question card | **G1** |
| **2. Design** (UI work) | G1 | Design written against the published specification: components and Variation IDs used, state list, edge cases. Pictures only if a member asked. Anything missing from the specification becomes a specification change first | **G2** |
| **3. Architecture + Plan** | G2 (UI work) or G1 | ADR or API contract where G3 applies; plan with tasks and a conflict table; tasks become Ready | **G3** (where it applies) **+ G4** |
| **4. Build** | G4 | One builder per issue in its own working copy; fix loop capped at 5 rounds; ambiguities logged as `Ruling: what — why — cost if wrong` | PR open |
| **5. Verify** | PR open | Applicable PR review gates in parallel; one fix wave | **G5a–e** (PASS, FAIL, or N/A with a reason) |
| **6. Localize + Document** (overlaps 4–5) | Stable API | Translation proposals to members (only approved words enter the catalog); docs; changeset | **G6, G7** where they apply |
| **7. Integrate** | Every applicable gate PASS or N/A | Self-merge: GitHub merges through auto-merge or the merge queue. PR-only and Approve-first: a member merges | Default branch green |
| **8. Release** (on demand) | Release batch ready, and for Library and Application, hosting defined | The release role opens the release PR; merging it makes CI tag, publish or deploy, and run the live check (recovery per §10) → result and "Rulings I made" posted on the release issue → lessons → plan review | **G8** |

**What runs on its own:** with Self-merge, everything: spec, design, plan, build, review, merge, migrations, release, and live deployment. With PR-only and Approve-first, everything up to the merge.

### 7.1 Work sizes

| Size | Phases | Notes |
|---|---|---|
| BUG | Skip 1–3 | The issue is the brief; a failing test first. Treated as S if it needs an API, security, or migration decision. The PM records G1–G4 as N/A on the issue |
| XS | Skip 1–3 | The issue is the brief. Same exception and same N/A record |
| S, M | All | |
| L | Split into M first | |

Sizes: XS is under an hour of work; S, under half a day; M, up to a day and one PR; L, more than that.

### 7.2 What waits for a member

**Agents do not wait for routine approval.** Situations that used to stop work trigger a safety net instead:

| Situation | What the agent does |
|---|---|
| Hard-to-reverse action | In the repository: proceed (git restores it). Live data: back up first (database dump), then proceed. Only an action nothing can undo, outside what the members authorized, is parked and reported |
| Security issue | Fix it at once, log a `security` issue |
| External side effect | Proceed if it is an authorized part of the pipeline; otherwise park and report |
| Plan broken | Re-plan, log a ruling, continue |
| `git clean -fdx` | Only inside the agent's own working copy |
| Database migration | Backup and a written recovery procedure first, plus a note on whether the previous build runs on the migrated schema |
| Merge | Self-merge: turn on auto-merge. PR-only and Approve-first: mark ready, list it for members, take the next item |
| Live deployment | Health check after deploy; on failure, restore the previous deployment if the previous build can run on the current database, otherwise run the tested recovery procedure (§10.2) |
| Issue done | Comment for the PM and end |
| A role missing or not starting | Open a P0 `process` issue; take the next Ready item |

**These wait for a member** (the agent continues other Ready work meanwhile, and applies a recommended option only where nothing below applies):
1. The intake (§0).
2. Merges, in PR-only and Approve-first projects, and the bootstrap PR that adds the required checks (§11.2).
3. Infrastructure changes in an Approve-first project: a member's approval of the change plan (below).
4. Language approvals: a new translated word enters the catalog only after a member's answer.
5. Changes to shared host files (§11): a member-approved diff.
6. The rare action that nothing can undo and that is outside what the members authorized.
7. A member's own setup steps (§11.3) and cutover confirmation (§0 Q0b). Agents never create accounts or type passwords, keys, or tokens; they use only credentials members saved, through registered tools.

**Infrastructure profile.** Servers and the network are not in git, so the rules are stricter:
- **Look freely, change only with approval.** Every change is a **change plan** posted on its issue as a comment whose first line is `## Change plan` (what, why, risk, how to undo, how access is kept). It runs only after a member's account posts a comment whose whole first line is `approved` (a trailing `.` or `!` is allowed), after the change plan was posted and after it was last edited, and the approval itself is not edited. Editing the plan or posting a new one needs a new approval; a member's later comment starting `revoked` withdraws it. What is approved is the plan as written; the least-rights account a member set up for the system is what limits what can actually be done. Agents comment through the bot identity, never a member's login (§11.1).
- **Who applies it:** the Infrastructure Maintainer or Network Engineer, activated again after the approval, applies it directly (not through CI); this is the one exception to "deploys run only through CI".
- **Never cut off the agent host or the members.** A change to the rules, ports, or settings remote access depends on also needs a member to say on the issue that they are online, and runs while they are.
- **Least access.** Each system gets its own account or token with only the rights granted, set up by a member.
- **Stop on refusal.** After one refused sign-in, stop and report, so the account is not locked.
- **Record.** `docs/inventory.md` is updated after every approved change.

---

## 8. Members and the dashboard

**GitHub is the record.** Whatever channel a member uses, the request, the decision, and the result end up on an issue in `LighthouseCollection/CTM`.

### 8.1 Channels

**Members use three channels for project work:**

| Channel | Use it for | Where |
|---|---|---|
| **The dashboard** | Logging a request, answering decisions, seeing what is open, waiting, done, the checks, the screenshots, across all projects | One dashboard for every project (§8.3) |
| **GitHub directly** | Issues from templates, comments, merges (PR-only and Approve-first) | `LighthouseCollection/CTM` |
| **The PM, live** | Talking it through: "what are you working on?", "do #123 first", "show me options". The PM writes anything asked onto an issue | The team's PM session, through remote access |

**One administrative channel:** the **control desk**, a session on a member's workstation that works on the agent host for setup changes: answering the intake, adding a role or member, restarting an agent, changing limits, adding a project. It acts only on a member's instruction and reports back.

**How work arrives.**
- A member logs a request (Bug, Feature, UI/UX, Question) on the dashboard, opens an issue from a template, comments, or tells their PM.
- The watcher hands it to the owning team's PM (§5.10).
- The PM routes it to the right role:
  - Library and Application: bugs to an engineer, with a failing test first; features to a spec, then an architecture plan, then engineers; UI changes to the Design Director, against the specification, then an engineer.
  - Infrastructure: a change plan from the Infrastructure Maintainer or Network Engineer, then approval (§7.2).
- After the merge (or release), the PM posts the result on the member's issue, with the PR, the before-and-after screenshots for UI changes, and the release link.

### 8.2 How agents talk to members

Everything is a comment on the GitHub issue, which the dashboard shows. Agents don't ask permission for routine work. They ask about *intent* only when a request can't be read any other way, and even then they go ahead with the recommended option and say so, unless the choice is one of those that wait for a member (§7.2). Every choice is reported with this card:

> **D-0123 · Data grid: row height in compact density**
> Context: one sentence of what we understood.
> **A (Recommended)** — 32px — risk: tight for dense scripts
> **B** — 36px — risk: fewer rows visible
> **C** — 28px — risk: below the touch minimum
> **Applied: A.** To switch, reply B or C. If switched, we redo: 1 token + snapshots.

**Rules for asking**
- **Pictures.** Screenshots that CI makes are always shared on the PR and the issue. Extra pictures (options, mock-ups) only when a member asks.
- **Don't ask when** the answer is in the published specification, the decision log, or the code, or the change is cheap to reverse (apply the default and say so).
- **Never ask twice.** Every decision becomes a `decision` issue and a decision file with date, reason, and the check that enforces it.
- **"Other" is not an ending.** The PM maps it back to options in the next card.
- **Feedback register.** Each member comment is tracked as open → accepted → applied (with a link). No silent drops.
- **No summary documents.** The dashboard shows the state at any time.

### 8.3 The dashboard

**One dashboard for every project**, with a project switcher. It is where members log requests and answer decisions, and it shows what every team is doing. It is Phase 0 project work, not part of the kit; where it is published and which projects it lists is decision D-0010.

**How it is built**
- A static web page built from one published design-system CDN (its stylesheet, components, and icons), chosen once for the dashboard in D-0010, whatever design system each project uses.
- **No server and no data store of its own.** It reads **GitHub live through the GitHub API** (GraphQL, one request per view where possible) and writes issues and comments back to GitHub. Nothing is cached as a source of truth, so it can't drift.
- **Where it lives:** one static site (for example GitHub Pages, or a page behind the site's sign-in).

**Access**
- Each member connects their own fine-grained GitHub key once. It allows read access, plus Issues read and write, for the repositories they choose. It is kept only in their browser, never in a repository, CI, or with an agent. Merges happen on GitHub, where the dashboard links each PR.
- Each member sees only what their GitHub account can see.
- Without a key, the page shows only how to connect.

**Views** (side navigation, each with a count, for the selected project or all projects)

| View | Shows |
|---|---|
| Waiting on you | Decisions to answer; setup steps (§11.3); PRs to merge (PR-only and Approve-first); change plans to approve (Approve-first) |
| New request | A short form (Bug, Feature, UI/UX, Question; description; optional picture) that opens a GitHub issue under the member's name |
| To decide | Open `decision` issues: question, context, options with risks, the option applied, an optional note. The answer posts as a comment under the member's name |
| To do | Open issues with an agent label, by priority, with the team and agent |
| Decisions | Every decision file: one line, why, options, who decided, status (active / superseded, linked / retired), the **check that enforces it** with its live result, and for design decisions the **specification section** it changed. Decisions with no check are listed so gaps are visible |
| Done | Issues closed in the last 30 days, with PR and release links, and the release issue's "Rulings I made" |
| Checks | Required checks on the default branch and on open PRs |
| Team | Each team's In-progress items and agent labels; Ready depth per lane; open `reminder` issues |
| Screenshots | Visual checks per PR: before, after, and the difference, filterable by component, theme, direction, and density (stored as CI artifacts, kept 90 days) |

---

## 9. Enforcement: making rules real

**Automated checks cost no AI tokens.** They run in CI on GitHub's machines and use CI minutes; AI turns are spent by agents doing work and by review gates, which run only where they apply (see "Conditional gates" under the Index). A check for a feature the project does not have is recorded N/A, not run. The kit ships check 11's registry reader; the CI workflows for all checks are Phase 0 work.

### 9.1 Design and code checks (Library and Application)

The single source is the published design specification and its tokens. Every rule reads from them.

1. No hex, rgb, or named colors outside reference tokens.
2. Radius, font sizes, spacing, and motion only from the specification's scales; nothing below its minimums.
3. No physical left/right; logical properties only.
4. No skipping token tiers; token names contain no values.
5. Contrast for every supported foreground/background pairing, in each supported theme, every commit.
6. Every component state in its manifest, checked against its stories.
7. Numeric columns: tabular figures and end alignment.
8. Visual regression on every PR in each supported theme at standard density; RTL and compact only for components whose text, direction, or density changed. A missing browser is a FAIL, not a skip. Screenshots go to the PR, the issue, and the dashboard.
9. **Locked-choice check:** the design system named in the project equals D-0002.
10. **Specification check:** every component and Variation ID the code uses exists in the published specification at the pinned version.

### 9.2 Process checks (the plan checks itself)

11. **Role registry:** the committed registry parses; every registered role has a definition, a label, and a runtime; adopted roles have provenance (the kit's `host/lib/registry.py check` does this).
12. **Settings in prose:** no document states a value of a registry setting.
13. **Decision coverage:** every decision has a linked check or an explicit "review only" reason; every design decision links the specification section it changed; decision numbers are unique.
14. **Instruction drift:** each runtime's instruction file equals `.agents/RULES.md` after its one-line generated header.
15. **Gate verdicts:** a required check on every PR that passes only when every applicable PR review gate has recorded PASS, or N/A with a reason, **on the PR's current head** (a new push makes earlier verdicts stale), and the issue records G1–G4 as PASS or N/A. Auto-merge waits for it.

### 9.3 Only where the project has them

- **Locale checks** (projects with translations): missing keys, unapproved translations, placeholder mismatches, missing plural forms, literal strings, unused keys.
- **Messaging standard** (projects with a UI): one pattern per message type (error, validation, destructive confirmation, success, empty state, loading, help), owned by the Technical Writer in `docs/content/messaging.md`, checked by a content check.
- **Behavior tests** (every component): renders each story without errors; every state reachable with the right ARIA; keyboard behavior and visible focus; RTL where configured; long and empty text don't break layout; no axe violations; all text from the catalog. A component with no behavior test can't merge. A bug fix comes with a test that fails before the fix. A flaky test is quarantined within 24 hours (§2, failure mode 4), never deleted.

### 9.4 Hard limits and guard rails

**Hard limits live outside the agent host.** Agents run on the host as an ordinary account, so anything on the host (a hook, a settings file, a file permission) can in the end be worked around by a determined agent. The limits that must hold are therefore placed where no agent can reach them:

| Limit | Hard limit (outside the host) |
|---|---|
| No direct or force push to the default branch; merges only when every required check passes | GitHub branch protection (pull requests required, required checks, no force pushes) |
| Only members merge in PR-only and Approve-first projects | The bot identity's GitHub permissions are set so that it cannot merge there |
| Releases and deploys only from CI | Deploy keys and publish tokens are held only by CI (protected environments); none is on the agent host |
| What an agent can do on a server or service | The least-rights account or token a member created for it; credentials an agent must never use (deploy keys, admin tokens, members' logins) are never stored on the host |

**Guard rails on the host catch mistakes.** They block the commands an agent might run by accident and explain why, but they read command text and run on the agent's own account, so they are not walls:

| Guard rail | Covers |
|---|---|
| The git pre-push hook (every checkout the launcher creates; it finds its project in the checkout's own git settings) | No push to the default branch (R1), no tag pushes (R3), nothing pushed during cutover (R5) |
| The guard (a pre-command hook, in runtimes whose hook is verified) | R1 default branch, R2 merges (only `gh pr merge --auto`, only by roles with merge rights), R3 releases, R4 Approve-first, R5 cutover, R6 secrets, R7 schedules and polling loops, R8 host settings and the kit, R9 other projects and folders, R10 hosts; the PM rule (the PM changes only Markdown, `docs/` and `decisions/`); PR review gates change no files |
| The launcher | Cutover (no agents start), one builder per issue, the claim, slots |

The guard rules are named R, not G, so they are never confused with gates. The kit's `ops/GUARD.md` specifies each one and its known limits, and every rule has a test with an allowed and a blocked case. A runtime whose hook is not verified gets no guard rails, only the hard limits; it may not run a PM.

**Stronger isolation (optional).** A host can also run its agents under a separate account that cannot read the secret store or change the kit and project settings. The kit does not set this up; `ops/GUARD.md` describes it.

### 9.5 Hooks

- **The guard** (§9.4) is the only pre-command hook, and the git pre-push hook the only git hook the kit adds; both are guard rails.
- The launcher's start message names the rules, the lessons and the agent's item, so no session-start hook is needed. The idle closer reads idleness from the session screen, so no activity hook is needed.
- Each hook must earn its place; no hook may start an AI turn by itself.

---

## 10. Release pipeline

### 10.1 Library profile

| Rule | Meaning |
|---|---|
| **Immutable versions** | A published version is never changed or reused; publishing fails if the version exists with different files |
| **One release PR, one tag** | The release role opens a release PR (versions and changelog from changesets). When it merges, CI creates the version tag and publishes the packages, the CDN files, and the API together, under the same version, with a deploy key no agent holds. No agent pushes a tag |
| **Real versions, batched** | Releases are batched when something is worth shipping; breaking changes only in a major version; removals announced with a deprecation window. An existing package continues its version history |
| **Two kinds of recovery** | A failed deployment: restore the previous one. A bad package release: keep it published, stop promotion, publish a corrective version |

CI's release job ships checksums and a `version.json` with every version; the live check fails without them. If hosting is open, releases run as a dry run and G8 cannot pass.

### 10.2 Application profile

A merge to the default branch deploys to staging. A release PR, when merged, makes CI tag the version and deploy it to production: backup → build → migrate → restart → health and live checks. On failure, the previous deployment is restored automatically when the previous build can run on the migrated database; otherwise the tested recovery procedure is run (restoring a backup can discard newer writes, so that is a recorded decision, not an automatic step). Staging and CI use made-up data only. A project without staging deploys to production only, from the release PR.

### 10.3 Infrastructure profile

The approved change is applied by the role that planned it (§7.2), verified, and recorded in `docs/inventory.md`. G8 passes when the change is verified; hosting is not needed.

---

## 11. Environment

| Item | Setting |
|---|---|
| Repository | `LighthouseCollection/CTM`; branch protection and required checks on `main`; a merge queue where available |
| Repository layout | Monorepo, no submodules, trunk-based |
| Agent host | **`Agents`**: a dedicated server used only for agents (account `agents`), shared by every project's teams. Sized from what actually runs; raised when new roles need it. The PM starter and the watcher run as user services; the watcher also runs the idle closer. Each session has its own memory limit |
| If no server is available | A member's desktop app with remote access, or cloud agent sessions, keeping the same session names; the team moves back when the server is available. Recorded in D-0009 |
| Accounts and billing | Agents run under one service account on the agent host: a **business seat dedicated to the host**, or **API billing with a spending cap** (D-0007). A member signs each runtime in on the host; the kit never stores that login. Never a personal plan. Members use their own seats |
| Remote access | **Only each team's PM** is started with remote access (where its runtime has it), under its session name. Folder trust is accepted for each working copy before a session starts |
| Folders | `/home/agents/ctm/`: `work/<repo>` (the checkout, with agents' working copies beside it in `work/`) and `notes/` (imported handoff and notes). The kit, its state and its log live elsewhere on the host (the kit's runbook lists them) |
| Credentials | §12 |

### 11.1 Identity

- **Bot identity.** Agents commit and comment as one GitHub identity that is not a member: a GitHub App or a dedicated machine account, logged in once on the host before the project is enabled. The kit sets each checkout's commit name and email from the host settings.
- The bot identity's permissions are the hard limit on merging (§9.4): in PR-only and Approve-first projects it cannot merge.
- In an Approve-first project, the host's GitHub login must not be a member's login, because a member's login could approve a change plan (§7.2); `dispatch.py check` and `pm.sh enable` refuse it.

### 11.2 Start-up order

Each step needs only what the steps before it produced. The project's `READINESS.md` lists the same steps with the exact commands.

**Once per agent host** (a member, with the control desk): `dispatch.py host`; `host/install.sh`, which runs every test; install the host rules as each runtime's global instruction file.

**Before the project is enabled** (a member, with the control desk):
1. Answer the intake (`dispatch.py new`).
2. Sign each runtime in on the host (business seat or capped API key), and log the host's GitHub CLI in as the bot identity (§11.1).
3. Create the repository if needed; protect the default branch (pull requests required, no direct or force pushes); with Self-merge, allow auto-merge. Clone it to `/home/agents/ctm/work/CTM`.
4. Store each host-held secret (`dispatch.py secret`); load SSH keys into the host's ssh-agent and add each SSH host's key to `known_hosts`.
5. Generate the files (`dispatch.py build`) and check the connections (`dispatch.py check`: no failures).
6. Copy the generated files into the checkout (`dispatch.py sync`) and commit them by a PR that a member merges.
7. Existing projects: copy the old team's handoff and notes to `/home/agents/ctm/notes/` and tag the old project's final state. If the old team is not yet stopped, the project starts in **cutover**.

**Enable and start:** `pm.sh enable <prefix>` (it creates the labels and, for Approve-first, checks the bot identity), then `pm.sh start <prefix>`. Each team's PM posts its first status; the lead PM opens the intake issue.

**Phase 0** (agents; for an Existing project, after cutover ends): the CI checks, which a member merges as the bootstrap PR and then makes required; the rest of the checklist; the master plan; the launch test (G0).

**Cutover.** While a member has not confirmed the old team is stopped, the PM reads and plans, opens issues and comments, but nothing is committed, pushed, opened as a PR, merged or relabeled, and the launcher starts no other agent. When a member confirms, the control desk ends it: `dispatch.py set <prefix> import.old_team_stopped=true`, `build`, `sync` (a PR), and `pm.sh restart <prefix>`, so the PMs start with the new rules.

### 11.3 Member setup checklist

Some steps only a member can do. They are listed in the project's `READINESS.md` and, once the PM has started, on the intake issue under "Waiting on you". Agents write the exact steps; they never do them. **Before enable** items must be done before the project is enabled; the others each have a fallback.

| Item | When | Member action | Until it is done |
|---|---|---|---|
| Agent account | **Before enable** | Sign each runtime in on the agent host, with the business seat or the capped API key | The team cannot run |
| Bot identity | **Before enable** | Create the GitHub App or machine account, give it access to `LighthouseCollection/CTM` (without merge rights in PR-only and Approve-first projects), and log the host's GitHub CLI in as it | Required: agents never act as a member |
| Generated files | **Before enable** | Merge the PR with the generated files (§11.2) | The PM has no rules to read |
| Auto-merge (Self-merge) | **Before enable** | Allow auto-merge in the repository settings | Agents cannot merge |
| Old team (Existing) | Before writes | Stop the previous team and tag its final state | **Cutover: no writes** |
| Remote access | Any time | Turn on remote access for the account in its admin settings | Members reach the team through the dashboard and GitHub |
| Dashboard key | Any time | Create a fine-grained GitHub key (read, plus Issues read and write) and connect it once | The member uses GitHub directly |
| Agent host resources | When adding roles | Approve raising cores or memory | New roles wait |
| System credentials (Infrastructure) | Before the first change | Create the least-rights account or token, and save it with `dispatch.py secret` | The team plans but changes nothing |
| Merge queue | Any time | Enable it (organization accounts) | Auto-merge with up-to-date branches (§5.10) |
| Staging (Application) | Any time | Create the staging environment and DNS | Production-only deploys from the release PR |
| Hosting | Before the first release | Decide where it runs or publishes | Dry runs only; G8 cannot pass |

---

## 12. Connections and secrets

### 12.1 The connection register

Every connection is recorded in the project's connection register (generated by the dispatch kit, kept in the repository as `docs/connections.md`). **It holds references, never secret values.**

| Kind | Recorded |
|---|---|
| Git remote | Hosting service, organization, repository, default branch, access method |
| SSH host | Alias, host, user, port, purpose, key reference |
| API | Name, base URL, purpose, authentication type, secret reference, public health URL, rate limits |
| Secret | Name, purpose, which roles or services use it, scope, storage location, rotation date |
| Public URL | Environment, URL, expected response |

Agents may also reach GitHub, the package registries, the published design specification, and the agent host itself (§9.4, R10).

### 12.2 Secret rules

- A secret value is never typed, copied, printed, logged, committed, or put in an issue, PR, chat, note, or screenshot. The one exception: a member types it at the hidden prompt of `dispatch.py secret`, which shows nothing.
- Values live in `/home/agents/.config/ctm/` on the agent host: the folder is readable only by `agents` (mode 700), each file only by its owner (mode 600). Tools read credential files literally; they never `source` them.
- Agents use connections only through pre-authorized tools (the Git client, the GitHub CLI logged in once, the SSH agent, configured service tools), and only at registered addresses. Agents never touch the secret store at all; members check it with `dispatch.py check`.
- **Only what agents' work needs is on the host.** The host cannot hide a file from an agent determined to read it, so every credential on the host is one whose least-rights use by an agent is acceptable. Anything agents must never use (deploy keys, publish tokens, admin tokens, members' own logins) is never stored on the host (§9.4).
- Each token has the least scopes its purpose needs, one purpose per token, and a rotation date.
- A secret pasted into a chat, issue, or terminal is treated as exposed and changed.
- Adding, changing, or removing a connection or secret is a recorded decision.
- `dispatch.py check` tests what it can without revealing any value: Git reachable (and branch protection, with GitHub CLI access), SSH key login, stored secrets present, private and within their rotation date, API health URLs answering, public URLs answering with the expected status. It marks what it cannot test (external secrets, APIs without a health URL) as **not checked**, not as passed.

---

## 13. Halt, incidents, and closing

**Halt** (one project or all):
1. One project: `pm.sh disable <prefix>` (stops its PMs and agents and keeps them stopped). All projects: also stop and disable the watcher timer and the PM starter service.
2. Turn off auto-merge on open PRs.
3. Stop other sessions as the members direct.
4. Record each step with its undo in the halt log (kept on the host, beside the kit's state; the runbook names it).

**Resume** only on a member's word: replay the halt log in reverse, one project at a time, checking each step.

**Incident** (a secret exposed, a harmful change, runaway cost):
1. Halt the project.
2. A member rotates any exposed secret.
3. Restore the last good state.
4. Report what happened, what was affected, and what was done, without any secret value.
5. Add the lesson.

**Closing a project:**
1. Halt it.
2. Archive the repository.
3. Revoke its secrets at their services and delete its secret folder.
4. Remove its folder from the host's project settings.
5. Keep its records read-only for the agreed period.
6. Record the closure.

---

## 14. Decision register: history, never design guidance

Decisions are recorded in `decisions/`, one file per decision (so two decision PRs rarely touch the same file), with: id, date, area, who decided, the decision, why, options, status, what supersedes it, the check that enforces it, and for design decisions the **specification section it changed**.

**Numbering.** D-0001 to D-0008 are the intake decisions and D-0009 to D-0015 the Foundation decisions. Every later decision, including those the kit writes when an intake answer changes, takes the next number after the highest on the default branch, never below D-0016. The lead PM keeps the numbering. If two PRs pick the same number, CI fails (§9.2 check 13) and the later PR renumbers.

**A project with its own log.** An Existing project that already keeps a decision log in another place or format keeps it (intake `existing.decision_log`). The kit then writes no decision files: every decision, the intake's included, goes into that log in the project's own format, with its next free number.

**Superseding.** A past decision is never rewritten; only its `status`, `superseded_by` and `check` may change. A full replacement sets `superseded_by: D-NNNN`. A partial replacement lists each part: `superseded_by: [{id: D-NNNN, scope: "what it replaces"}]`, and the old decision stays `active` for the rest.

**Design decisions live in the specification.** Choices about the look (corners, type, density, accent, dark mode, table pills, icons) are made by changing the published design specification. The decision record says why and links the specification section; it is never the guidance itself. A design decision is not done until the specification shows it. Until it does, the published specification still applies.

### Intake decisions (§0)

| # | Decision | Answer |
|---|---|---|
| in the project's own log (`decisions.yaml`) | Mode, project type, name, prefix (answering the intake authorizes Phase 0) | `Existing` / `Application` / `CTM` / `ctm` |
| in the project's own log (`decisions.yaml`) | Design system and its published specification (**locked**) | `Plenix` at `https://design-system.lighthouseway.org/`, version `1.7.0 (pinned in ctm/settings.py; upgraded automatically by plenix-upgrade.yml, D-0005)` |
| in the project's own log (`decisions.yaml`) | Repository, and for Existing the import source and cutover status | `LighthouseCollection/CTM`. Imported from CTM3 on VM 131 (folder /home/cc/ctm3, PM "CTM3 - PM"); old team stopped: yes. |
| in the project's own log (`decisions.yaml`) | Hosting and environments | `production https://ctm.lighthouseway.org/health/` |
| in the project's own log (`decisions.yaml`) | Merge rights | `PR-only` |
| in the project's own log (`decisions.yaml`) | Members and teams | `Fr. Raphael Maher (@LighthouseCollection, team core)` |
| in the project's own log (`decisions.yaml`) | Runtimes and billing | `PM on claude-code; other roles on claude-code; business seat dedicated to the agent host` |
| in the project's own log (`decisions.yaml`) | Connections | The connection register (`docs/connections.md`) |

### Foundation decisions (Phase 0, asked in one batched card with a recommendation and a default each)

Pending until Phase 0 records them in `decisions/`.

| # | Decision | Question |
|---|---|---|
| D-0009 | Agent host | `Agents` (default) or the fallback (§11); memory limit per session and for the PM |
| D-0010 | Dashboard | Where it is published; which projects it lists; which design-system CDN it uses |
| D-0011 | Release cadence | Batched on demand once checks pass (default), or on a CI schedule (a CI job, not an AI turn) |
| D-0012 | Product goals | The 3–5 outcomes the master plan is built around (only if the intake and repository don't answer it) |
| D-0013 | Product languages | Primary language; additional languages; RTL in scope? Every new translated word goes to members as a proposal; only an answer enters the catalog. (Separate from the language agents write to members in, a host setting) |
| D-0014 | Mobile scope | In scope for the first release, or deferred |
| D-0015 | Second runtime | A reviewer gate from a different model, on standby, or none |

**"Keep as defined"** means the published specification is the baseline. Agents may fix defects within it (contrast below AA, wrapping, uneven heights, sizes below the minimum) without asking. They may not change the look without a specification change.

---

## 15. Sources of truth and search

| Question | The single source |
|---|---|
| What a member wants and approved | The member's own words, recorded on the GitHub issue with who, when, and the scope |
| What work exists and its state | GitHub issues, PRs, the board |
| How the code works | The default branch |
| **What the design is** (components, variations with their Variation IDs, defaults, sizes, colors) | **The published design specification.** Canonical |
| **Why, when, and who decided it** | **The decision log**: history, linking to the specification section it changed |
| **What actually ships** | **The published version on the CDN or in production**, plus the project's configuration |
| Settings, roles, members, runtimes | The intake, and the files generated from it |
| Rules | The host rules, then `.agents/RULES.md` and `docs/project-rules.md` |
| Lessons | `docs/lessons.md` |
| Connections | The connection register (references only) |

When sources disagree, this order wins: a member's latest recorded answer on the issue (for a design choice, once the published specification shows it; until then the specification applies), then the published specification (for design), then the host rules, then the project's rules, then earlier decision records, then everything else.

**Search.** A per-project search index (a separate host tool, not part of the kit) covers the specification (section by section, linked to the live page), the rules, decisions, documents, issues, PRs, comments, and handoff notes. It never mixes projects and makes no paid AI calls. For design questions the specification ranks first; decisions appear only as "why it is this way". Results are evidence: open the source before relying on it. AI summaries and transcripts are pointers only.

---

## 16. Sources

- Agent frameworks and roles:
  - obra/superpowers
  - msitarzewski/agency-agents
  - FoundationAgents/MetaGPT
  - OpenBMB/ChatDev (`chatdev1.0`)
- Design and UX skills:
  - pbakaus/impeccable
  - plugin87/ux-ui-agent-skills
  - neuhai/uxagent
  - jakubkrehel/skills
  - educlopez/ui-craft
  - DonkeyKing01/tasteful-ui-skill
  - JacobLinCool/ux-discovery-interviewer-skill

---

## Appendix A. Seed lessons

`dispatch.py build` seeds `docs/lessons.md` with these (once; later builds keep the project's own lessons). They are mistakes earlier projects made, each of which cost real rework, so a new project's agents don't repeat them. Add a line whenever a mistake costs a review round, a failed deploy, or a reverted merge.

| # | What went wrong | Rule now |
|---|---|---|
| A-01 | Two engineers built the same issue; one finished PR was thrown away | Claim before building; the first claim wins |
| A-02 | A required check was blocked by its own cancelled run | Required checks never use `cancel-in-progress` |
| A-03 | `check \| tee log` hid failures and a broken upgrade nearly merged | Any script whose result gates a merge or release uses `set -o pipefail` |
| A-04 | Agent reports said DONE without proof | A report is a claim until `git log`, the diff, and the checks confirm it |
| A-05 | A claim about the repository was made from a stale local clone | Fetch and check the remote default branch before claiming anything about the repository |
| A-06 | A late, large merge silently dropped controls | Integrate small and often; before resolving a shared file, list what each side added and confirm both survived |
| A-07 | Choices were never written down, so layouts flip-flopped | Every choice is a decision with an enforcing check; for design, the specification shows it |
| A-08 | `main` had no branch protection and stayed red for weeks | Required checks on the default branch from day one; a red default branch is a P0 bug |
| A-09 | Two agent teams worked with different rules | One rulebook for every team and runtime; GitHub is the record every channel ends in |
| A-10 | A member was re-asked after each answer | The answer is final: act on the sensible reading, say it in one line, handle all answers in one pass |
| A-11 | A member pointed at a working example and a different one was built | When a member points at a working example, ship that example first, then improve it |
| A-12 | A "pushed" report was wrong because the branch was locked in the merge queue | Check the push result before reporting; dequeue, push, then re-queue |
| A-13 | A PR merged with an open gate change because the label arrived after it entered the queue | When requesting changes, dequeue the PR first |
| A-14 | Hand-trimmed test fixtures hid missing fields | Fixtures come from, or are checked against, the contract files |
| A-15 | An upgrade removed a file that string-only tests missed | Upgrades fetch every referenced file before merging |
| A-16 | The config said 8 slots while a document said 4 | Settings live only in the intake and its generated files; documents name them |
| A-17 | Headless agents never showed in the session list, so nobody could reach them | Every session is interactive and named; the PM has remote access where its runtime has it |
| A-18 | A personal plan's spending limit stopped every agent at once | A business seat or capped API billing for agents |
| A-19 | A rename changed only the local session name | Rename by reconnecting remote access under the session name (`pm.sh rename`) |
| A-20 | The contact agent was lost among the other agents | The PM is `CTM4 - PM` (or `CTM4 - PM (<team>)`; hyphen), others `CTM4 · <title> #<issue>` (dot), so the PM sorts first |
| A-21 | A new project's agent was started inside another project's repository | One project, one repository, one folder, one registry |
| A-22 | A password typed at the shell prompt showed on screen; a quote mark in it later broke a script | Secrets only through `dispatch.py secret`; credential files read literally; stop after one refused sign-in |
| A-23 | A decision record said "fully replaced" while its replacement said "the rest still holds", so search hid the design that applied | Partial and full replacements are recorded explicitly (§14); the specification says what applies |
| A-24 | The design specification existed in two repositories and tools read different halves | One canonical copy per source; anything else is generated |
| A-25 | An old AI memory note was quoted as a decision | AI summaries are pointers; open the source |
| A-26 | Timers woke agents every few minutes with nothing to do and used the allowance | No AI turn without new work; the watcher is plain code |
| A-27 | A deploy check ran on an empty input and reported success | Release gates are fail-closed and tested with a deliberate fault |
| A-28 | Search-engine experiments ran for days without an exit criterion | Every experiment states its exit criterion and stops when it is met or missed |
| A-29 | An agent typed into a session while a person was half-way through a message | Deliver into a session only when it is idle and its input box is empty; a screen that cannot be read counts as busy |
| A-30 | A check in the agent's own sandbox was treated as a security wall | Put hard limits where agents cannot reach them; keep host checks as guard rails |

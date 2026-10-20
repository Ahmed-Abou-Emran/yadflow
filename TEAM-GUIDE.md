# Yadflow Team Guide — how to use the workflow with 1 Product + 3 code repos

**Yadflow** (*yahd-flow* — from **يد**, Arabic for "hand"): shared project memory and workflows for
teams building with AI. On npm as `yadflow`.

What it gives a team, in short:

- **One shared record.** Plans, decisions, contracts and reviews live as files in one repository,
  and both people and AI assistants read them.
- **Clear handoffs.** `yad next` names the next action and its owner. `yad claims` shows who is
  editing what. Review conversations happen on real pull requests or merge requests.
- **Less busywork.** Skills draft each document. `yad ship` commits and opens the pull request.
  Drafts are saved for you (on Claude Code and Cursor).
- **A person decides.** Every planning step waits for human approval. *AI builds. The hand decides.*
  Yadflow is not a chat tool: the conversation stays in your pull requests and your usual channels.

This is the plain-language guide for a developer team. The [`README.md`](README.md) is the short
introduction. If you only read one page before starting, read this one. For depth, see [`docs/CLI.md`](docs/CLI.md) (commands),
[`docs/SKILLS.md`](docs/SKILLS.md) (every skill), and [`docs/WALKTHROUGH.md`](docs/WALKTHROUGH.md)
(the by-hand, end-to-end path) — or learn by doing in the
[guided tutorial](https://abdelrahmannasr.github.io/yadflow/tutorial/).

---

## 1. The big picture

### Your four repos

You will have **four separate git repos**, each with one job, plus the **yadflow** tool itself:

```
  yadflow         ──►  the TOOL
  (npm package)        The `yad` CLI and the 38 workflow skills, installed from npm
                       (`npx yadflow …` or `npm install -g yadflow`). You never clone it,
                       and no real product work happens inside it.

  Product         ──►  the THINKING
  (new repo)           All epics, contracts, stories, reviews, and state.
                       Lives under: epics/EP-<slug>/

  code-repo-1     ──►  the CODE
  code-repo-2          Real application code. Each story's spec lives here too,
  code-repo-3          under: specs/<story-id>/  — and every PR links back to its
                       story in the Product.
```

```mermaid
flowchart LR
    classDef prod fill:#fcf3cf,stroke:#b7950b,color:#000
    classDef code fill:#d6eaf8,stroke:#2471a3,color:#000
    src["yadflow<br/>npm package: CLI + skills"]
    prod["Product<br/>epics · contracts · stories · state"]:::prod
    r1["code-repo-1"]:::code
    r2["code-repo-2"]:::code
    r3["code-repo-3"]:::code
    src -. install skills .-> prod
    prod -- connect-repos:<br/>cache code-map --> r1
    prod -- connect-repos:<br/>cache code-map --> r2
    prod -- connect-repos:<br/>cache code-map --> r3
    r1 -. specs & PRs link back .-> prod
    r2 -. specs & PRs link back .-> prod
    r3 -. specs & PRs link back .-> prod
```

**The handoff rule:** everything *up to and including the locked contract* lives in the **Product**.
Everything *from the spec onward* (specs, tasks, code) lives in each **code repo**.

### The whole workflow, end to end

Setup is one-time. The **Shape** part is human-gated and runs once per epic in the Product; **Build**
runs once per story per code repo; **automation** is opt-in, switched on by the team with `yad dial`. `yad-status` reads it
all; `yad-product-bridge` mirrors Shape reviews to real PR/MRs on the Product.

```mermaid
flowchart TD
    classDef gated fill:#fdebd0,stroke:#ca6f1e,color:#000
    classDef canauto fill:#d6eaf8,stroke:#2471a3,color:#000
    classDef locked fill:#eaecee,stroke:#566573,color:#000,stroke-dasharray:5 3
    classDef artifact fill:#fcf3cf,stroke:#b7950b,color:#000
    classDef sentinel fill:#d5f5e3,stroke:#1e8449,color:#000

    subgraph SETUP["0 · One-time setup (team lead, per project)"]
      direction TB
      inst["yad new / init / join<br/>install skills + wire each repo"]
      conn["yad-connect-repos<br/>cache each repo's code-map"]
      sync["yad-sync-repos<br/>switch every repo to default branch + ff pull"]
      inst --> conn --> sync
    end

    subgraph FRONT["A · Shape — Product · human-gated · once per epic"]
      direction TB
      an["yad-analysis<br/>optional → analysis.md"]:::artifact
      ep["yad-epic<br/>epic.md · assigns EP-&lt;slug&gt;"]:::artifact
      ar["yad-architecture<br/>architecture.md + locked contract.md"]:::artifact
      ui["yad-ui<br/>optional · ui-design.md + DESIGN.md<br/>skippable N/A for UI-less epics"]:::artifact
      st["yad-stories<br/>repo-tagged stories"]:::artifact
      tc["yad-test-cases<br/>test-cases.md + automation tests"]:::artifact
      gAn{{"gate · analysis"}}:::gated
      gEp{{"gate · epic<br/>1 approver"}}:::gated
      gAr{{"gate · architecture<br/>1 approver · count asks 3"}}:::gated
      gUi{{"gate · UI · 1 approver"}}:::gated
      gSt{{"gate · stories<br/>1 approver"}}:::gated
      gTc{{"gate · test cases · 1 approver"}}:::gated
      rfb(["ready-for-build"]):::sentinel
      an --> gAn --> ep --> gEp --> ar --> gAr --> ui --> gUi --> st --> gSt --> tc --> gTc --> rfb
    end

    subgraph BUILD["B · Build — per story, per code repo"]
      direction TB
      sp["yad-spec<br/>→ specs/&lt;story&gt;/"]
      im["yad-implement<br/>1 task = 1 branch = 1 commit"]:::canauto
      ck["yad-checks<br/>spec-link · contract-check · risk-map · build/test/lint<br/>lineage-check · epic-open · reconcile-debt<br/>verified-commits · commit-message · pr-title · pr-template"]:::canauto
      prm["yad-ship: commit + open PR/MR"]
      eng{{"yad-engineer-review<br/>human · never automated"}}:::locked
      merged(["merge → build-log.json"]):::sentinel
      sp --> im --> ck --> prm --> eng --> merged
    end

    subgraph AUTO["C · Automation — switched on & reversible"]
      direction TB
      run["yad-run<br/>the dial (yad dial) + trust-log.json"]:::canauto
      cpt["yad checkpoint --push<br/>commit trust-log · build-log · build-state (chore(product))"]
      kill["yad kill → all advance: human"]
      run --> cpt
      run --- kill
    end

    conn --> an
    rfb --> sp
    run -. drives Build steps set to auto .-> im
    bridge["yad-product-bridge<br/>review PR/MR ↔ file ledger"]:::gated
    bridge -. syncs approvals .-> gEp
    status["yad-status — read-only view over all of it"]
    status -. observes .-> FRONT
    status -. observes .-> BUILD
```

**Legend.** 🟨 **artifact** = an author step writes a file and stops · 🟧 **gate** = a human review
that must pass (`open → comment → approve → advance`) · 🟦 **can run on auto** = a Build step the team
may set to advance on its own with `yad dial` · ⬜ dashed **locked** = the engineer review and every
Shape review gate, **permanently human**.

---

## 2. The workflow has three parts

- **Shape = decide.** Done once per epic, in the **Product**. Always human-approved — nothing
  auto-advances. This is where you agree on the epic, the architecture, the locked contract, the UI, and
  the stories.
- **Build = make it real.** Done once per story, per code repo, **inside that code repo**. Spec → implement →
  check → ship.
- **Run = operate it.** Release and Operate — the part that closes the loop back to Shape. Named
  here because the vocabulary is settled, but **planned, not built yet**.

Each step writes a file and then **stops at a gate**. A human moves it forward. That is the whole idea.

### Inside the parts: six phases

A part is a big chunk. A **phase** is the smaller named stretch of work inside it, and every step
belongs to exactly one:

| Phase | Part | The steps in it |
|---|---|---|
| Discover | Shape | analysis · epic, each with its gate |
| Design | Shape | architecture, with the locked contract · ui-design, each with its gate |
| Plan | Shape | stories · test-cases, each with its gate |
| Build | Build | spec · tasks · implement · checks · engineer-review |
| Release | Run | **planned, not built** — release notes · version · deploy record · gate |
| Operate | Run | **planned, not built** — defects · feedback · retrospective · improvements |

`yad next <epic>` prints this list with your current phase marked, so you can see where you are
without counting steps. The last two are shown greyed, because the lifecycle does not stop at merge
even though the tool does not run those phases yet.

Once the stories gate passes, the epic is in **Build** and stays there for the rest of its life — the
individual Build steps run per story per code repo, so the epic-level view names the phase rather than
the step. A stub epic shows no phase line at all, because it does not walk this lifecycle.

The **Foundation** is not on this list either, because it is not a feature epic. It is the **Product
level**: it runs once per product, before any epic, in its own folder `foundation/`. It has one phase of
its own, also called Foundation, and `yad next` prints `phase: Foundation` for it instead of the six.
Start one with `yad foundation new`, then write it with the `yad-discovery` skill. Its approval is meant
to come before feature work; `yad next` tells you when epics are going ahead of it, and does not block
them. A product made before this release may still keep it in `epics/EP-discovery/` —
[shape 8](docs/migrations/shape-8.md) explains how that converts.

Phases are worked out from the step you are on. They are not written into any file, so there is
nothing to keep in step and nothing to migrate.

---

## 3. One-time setup (the team lead does this once)

A **workspace** is one folder that holds the Product (`product/`) and your code repos side by side.
One command makes it. Each code repo stays its own separate git repo (its own `.git`).

**a. Create the Product.** Pick the command that fits:

```bash
npx yadflow new acme     # a new product: makes acme/product/, runs git init, then the guided setup
npx yadflow init         # code repos you already have: run it in the folder that holds them
```

`new` creates nothing online. At the end it prints the `gh repo create` / `glab repo create` line that
puts the Product on GitHub or GitLab — run it yourself. `init` makes `product/` beside your repos and
asks, one repo at a time, whether to connect it.

**b. The guided setup runs inside it.** Both commands run the same wizard as `npx yadflow setup` (which
you can also run by hand inside an existing Product repo). It installs the skills into the agent folders
you pick, detects the Product platform, connects your code repos, and wires each one (CI gates, PR/MR
template). It also leaves a small `.yad-workspace.json` in the workspace, so `yad` finds the Product
from inside any repo it registers. You don't need to scaffold anything else — the first `yad-epic` run
creates `epics/EP-<slug>/` and its state files for you.

**c. Push the Product and invite the team.** Run the printed `gh`/`glab` line, commit, and push. Then
teammates join with `yad join <url>` (section 4).

> Re-run `npx yadflow check --fix` after any workflow update — it reports what is
> missing / drifted / stale and reconciles only what changed (it never re-asks for what you already
> answered).
>
> **Upgrading to a new yadflow version:** in the Product, run `npm install -g yadflow` (the latest
> release), then `yad migrate` (a preview of the state files the new release would rewrite — it writes
> nothing), then `yad migrate --apply` (it rewrites them and keeps a `<file>.yad-orig` copy of each), then
> `yad update` (it installs newly-added skills, updates changed skills, and re-copies updated gate
> scripts into your connected repos), then `yad doctor` to confirm. On a minor or patch release
> `yad migrate` usually has nothing to do. Coming from 3.x? Read
> [upgrading to 4.0](docs/migrations/upgrading-to-4.md) first.
>
> **Landing the upgrade for the whole team:** `npx yadflow update` only writes the changed files into
> the working trees — someone still has to commit them across every repo. Run `npx yadflow update
> --push` to have yadflow **commit each repo's changes and push them straight to the default branch**
> of the Product and every connected repo, as one `chore(yad-update): sync SDLC install to yadflow
> vX.Y.Z` commit per repo. It stages only what it wrote (never `git add -A`) and only commits on a
> repo's default branch — a repo on a feature branch is skipped with a warning, never disturbed.
> Because it pushes directly to the default branch there is **no PR/MR**, so the normal gate suite is
> skipped; a dedicated push-on-default-branch **`yad-update-guard`** (a GitHub workflow / GitLab CI
> fragment) re-checks just two things on the commit — that it carries a **signature GitHub or GitLab
> marks as Verified** (`verified-commits`; there is no list of allowed authors — write access to the
> repo decides who may commit) and follows the **commit convention** (`commit-message`). yadflow prints an
> announce banner before it starts: **tell the team and pause merges on those repos until it
> finishes**, so the direct-to-default-branch pushes don't collide with in-flight work. (Direct pushes
> to the default branch must be permitted for the committer — adjust branch protection accordingly.)

**Where the skills live.** The CLI installs the skills into the Product itself — into the agent
folders you picked (`.claude/skills/`, `.agents/skills/`, and so on), not into your home folder. You
have two choices:

- **Commit them.** Anyone who clones the Product gets the skills with it.
- **Have git ignore those folders** (ignore the folder itself, for example `.claude/`). Then each
  person gets a private copy when they run `yad join`, and `yad update` refreshes it.

There is no manual install any more: the skills call `yad` commands, so they need the CLI anyway.

**d. Wire each code repo.** The setup already does this for every repo it connects. For a repo you
add later, run from inside the Product (or with the repo path):

```text
yad-checks          repo:<repo> action: wire   # installs the CI gates (merges with existing CI, never clobbers)
yad-pr-template     repo:<repo> action: wire   # installs the PR/MR template + risk routing
```

> **Wiring is additive.** `yad-checks` detects any CI you already have and *merges* the gates in
> (GitHub: a separate `yad-checks.yml`; GitLab: an `include:` of `.gitlab/ci/yad-checks.yml`) — it
> never edits a foreign workflow. Re-running any `wire` is a no-op.

**d2. Wire the Product itself** (so the Shape review can run through real PRs on the Product):

```text
yad-connect-repos action: detect-product                              # records the Product's platform in .sdlc/product.json
yad-pr-template     repo:product action: wire                         # Product's Shape PR/MR body template
yad-checks          repo:product action: wire                         # Product gates: commit-message, pr-title, pr-template, ledger-guard, verified-commits
yad-product-bridge      action: wire                                  # merge-time gate sync (CI runs `yad gate ci` when a review PR/MR is merged)
```

There is no list of reviewers to set up. yadflow keeps no roster: anyone with access to the Product repo
can approve, and the platform records who did — each approval is stored under the approver's
GitHub/GitLab **login**. A review PR requests no reviewers, so ask them on the PR itself.

**Who writes the gate ledger.** The **gate ledger** is the set of files that record where each epic
stands (`state.json`, `approvals.json`, `comments.json`, `reviews/`). The Product setting `ledger` in
`.sdlc/product.json` decides who writes it:

| Setting | Who writes the ledger | How a review advances |
|---|---|---|
| No platform | your machine | `yad gate comment`, `yad gate approve … --by <name>`, then `yad gate advance` (see section 10) |
| `ledger: local` + a platform | your machine | reviewers approve on the review PR/MR; after the merge, `yad gate sync` pulls that into the ledger and advances the step |
| `ledger: verified` + a platform | CI only | reviewers approve on the review PR/MR; the **merge** makes the Product's CI run `yad gate ci --merged`, which writes the ledger. `yad gate sync` only shows what CI will do |

With no platform, skip d2. (An older Product may still say `bridge_enabled: true` instead of
`ledger: verified`; `yad migrate` adds the new key.)

In verified mode you usually don't run anything after the review: the **merge** of a review PR triggers
the gate in the Product's CI, and the ledger update is committed straight to the Product's default branch (`git pull`
to see it). Nothing fires pre-merge — approvals and change requests live on the platform, which is the
source of truth while the review is open, and CI never touches the review branch (so an in-flight
approval is never dismissed by a CI commit). CI never approves or merges — the merge click stays human.
GitLab caveat: a bare approval is only picked up by the ~15-min scheduled sweep (one-time schedule +
`SDLC_GATE_TOKEN`; recipe in the skill). That sweep re-visits each merged review for a week; on a yadflow
carrying the #163 fix that costs a read, not a commit — the ledgers are written in a canonical order,
so an unchanged approval record re-serializes to an identical file. On older versions it committed the
reorder every 15 minutes; the workaround there is to disable the schedule.

**e. Connect your code repos to the Product (so the brain knows what's already built).** From inside the
Product, run once per code repo — and again any time you add a new one:

```text
yad-connect-repos action: connect repo:<repo> path:<path-or-git_url>
```

This registers the repo in `.sdlc/repos.json` and caches an AI-readable picture of it (a Repomix pack +
a lightweight **code-map** of its existing endpoints/events/data-models/modules, secret-scanned). The
Shape steps then read that map so they don't re-design or contradict code that already exists.
It clones/fetches as **you** (your own SSH key or git credential helper — GitHub *or* GitLab, no stored
tokens). Greenfield with no code yet? Skip this — the brain just proceeds. When a repo's code moves,
`yad-connect-repos action: refresh repo:<repo>`; to see freshness, `action: list`.

**f. Optional tools.** The workflow uses these if present and **degrades gracefully** (and records it)
if they're missing: **Spec Kit** (`/speckit.*`), **Impeccable** (`/impeccable …`), **Repomix**
(`npx repomix@1.18.1`, the vetted version, used by `yad-connect-repos` and `yad-backfill`), **CodeRabbit** (advisory AI review),
**DeepTutor** (`deeptutor`, the learning layer's tutor — used by `yad-connect-learning`/`yad-learn`,
degrades to harness-native).
You can start without any of them.

---

## 4. Onboarding a team member (every developer, copy-paste)

1. Join with one command, using the Product's git URL:

   ```bash
   npx yadflow join <product-url>
   ```

   It clones the Product into `<folder>/product/`, then every code repo the Product registers, beside it.
   Then it does only the per-machine steps: the skill copies the Product's git ignores, and a git
   **pre-commit hook** (a small script git runs before each commit) in your clone. A repo that fails to
   clone is named and skipped; run `yad join <url>` again to fetch what is still missing.

   Last, it records you as a **team member** (`yad member add`). It logs you in to GitHub or GitLab if
   you are not logged in yet. Then it asks the platform which of your emails are **verified** (confirmed
   as yours by the platform), and writes `.sdlc/members/<platform>-<your login>.json` with your accounts
   and those emails — stored as one-way fingerprints (hashes) in the file. The proof commits on that branch
   are authored by each email, the same way your normal commits show it, and anyone who already knows an
   address can check it against a fingerprint. It puts this file on a branch of its own and opens a pull
   request for it, so it never touches your checkout. If anything goes
   wrong there, join still finishes and tells you to run `yad member add` later. The file only says
   "these accounts and emails are one person"; it gives no access and no role.
2. **A repo added after you joined?** Run `yad repo clone` in the Product. It clones every registered
   repo that is missing on this machine. `yad repo list` shows which ones are **not cloned**.
3. That's it. Open your agent **in the Product** to work on epics; open it **in a code repo** to
   build stories. `yad next` tells you what to do first.

To run a skill, just ask your agent by name — e.g. *"run `yad-epic`"*. All state is plain files
you can also read and edit directly.

---

## 5. Running an epic — Shape (in the Product)

Do these in order. After each author step, the matching review opens and **waits** — you clear it with
`yad-review-gate` (`action: open → comment → approve → advance`).

Either of the first two steps can lay the track for you, or you can have the engine do it first:
`yad epic new <slug>` writes the epic's step chain and its empty ledgers, then the skill authors the
document against it. The chain comes from a **lifecycle profile** — `classic` is the 10-step route and
the default, `--profile analysis-first` is the 12-step one. Two short lanes exist for work that is not
the size of a feature: `--profile chore` is 4 steps for upkeep somebody has already decided on, and
`--profile spike` puts the analysis in front of those for a timeboxed question. Neither short lane has
an architecture gate, so neither may change the shared contract, and the choice is final — there is no
re-seed. It writes no `epic.md`, no branch and no
commit, and refuses an epic that already has a chain.

| # | Run this | It produces | Then approve at |
|---|----------|-------------|-----------------|
| 0 *(optional)* | `yad-analysis` | `analysis.md` — the analyst's discovery brief (assigns the `EP-<slug>` ID, seeds state) | analysis review |
| 1 | `yad-epic` | `epic.md` (reads `analysis.md` when present; otherwise assigns the `EP-<slug>` ID and seeds state itself) | epic review |
| 2 | `yad-architecture` | `architecture.md` + the **locked** `contract.md` | architecture review *(contract: count 3)* |
| 3 *(optional)* | `yad-ui` | `ui-design.md` + `DESIGN.md` | UI review — skip N/A for a UI-less epic with `yad skip <epic> ui-design --reason …`, or `yad defer` it to design later (add `--debt` if it is owed back — `yad next` reminds you until it is paid) |
| 4 | `yad-stories` | one file per story, `stories/EP-<slug>-S0N.md`, each tagged with the repos it touches | stories review |
| 5 *(parallel)* | `yad-test-cases` | `test-cases.md` covering the stories (+ the automation tests when a testing tool is connected) | test-cases review |

Step 0 is **optional**: run `yad-analysis` first for a dedicated, gated discovery pass; skip it
and the epic step does that analyst shaping inline. Each author step opens its own branch
(`<step>/EP-<slug>`) at the start. When the **stories** gate (step 4) passes, the epic state reaches
**`currentStep: ready-for-build`** — you can build **now**. Step 5 (`yad-test-cases`) is a **parallel,
non-blocking** track: it opens at the same moment and the tester works it **alongside** Build;
its review never blocks building.

> **The brain is code-aware.** If you connected your code repos in setup (step 3e), each author step
> first loads the connected repos' **code-maps** — so the epic references what exists, the architecture
> **cross-checks the contract against existing endpoints/models before locking it**, the UI reuses
> existing components, and stories anchor to real modules. Each artifact records what it read in its
> `code-context:` frontmatter. If a repo's code has moved since you connected it, the step warns and
> points you at `yad-connect-repos action: refresh`.

**The gate, every time** (`yad-review-gate`) — the same loop for all five reviews. Commenting never
advances; only `advance` moves forward, and only when the rule is met:

```mermaid
flowchart LR
    o["open<br/>show artifact"] --> c["comment<br/>reviewers leave notes"]
    c -->|owner addresses,<br/>edits in place| c
    c --> ap["approve<br/>platform login"]
    ap --> adv{"advance?<br/>rule met?"}
    adv -->|no — tells you<br/>what's missing| o
    adv -->|yes| nxt(["next step"])
```

- `action: open` — show the artifact; reviewers leave comments. *Commenting never advances.* If the Product
  is on a platform (step 3d2), this also opens a review **PR/MR on the Product** for the artifact
  (`yad gate open`).
- **With a platform, the merge is what advances.** Reviewers approve and comment on the review PR/MR.
  Once the approvals are enough and every comment thread is resolved, a person merges it. Then:
  - `ledger: local` — run `yad gate sync <epic>` (or `action: sync`). It pulls the approvals and comments
    into the ledger and advances the step.
  - `ledger: verified` — nothing to run. The Product's CI runs `yad gate ci --merged` at the merge and
    commits the ledger to the Product's default branch. `yad gate sync` is only an advisory view here.
    Nothing runs pre-merge: while the review is open the platform holds the state (native approvals +
    threads), and CI never touches the review branch, so an in-flight approval is never dismissed by a
    CI commit. A scheduled job re-checks recently-merged reviews as a safety net.
- **With no platform**, record the review by hand: `yad gate comment <epic> <artifact> --by <name>`,
  `yad gate approve <epic> <artifact> --by <name>`, then `yad gate advance <epic> <artifact>`. `advance`
  moves forward **only if** the rule is met; otherwise it tells you what is still missing.

---

## 6. Building a story — Build (in a code repo)

From a `ready-for-build` story, do this **inside each code repo the story is tagged with**:

1. **Spec** — `yad-spec story:<id> repo:<repo>` → writes `specs/<story-id>/` (spec/plan/tasks +
   `link.md` back to the story). It *quotes* the locked contract; it never widens it.
2. **Implement** — `yad-implement story:<id> repo:<repo> task:<T0N>` → **one task = one branch = one
   commit**. Repeat per task. The first run installs a `.gitmessage` commit template: the human author
   owns the commit, with a required `Task:` trailer and an optional per-commit `Co-Authored-By:` for the
   AI tool that helped (chosen from `config.yaml` `build.ai_coauthor.allowed`).
3. **Check** — `yad-checks repo:<repo> action: run` → the gates must pass: spec-link,
   contract-check, build/test/lint, verified-commits (every commit signed with a
   platform-Verified key — on the Product and every repo; write access decides who can author), the
   pattern gates commit-message / pr-title / pr-template, and the feature-thread gates: lineage-check
   (a change, defect or hotfix epic must thread to a real parent), epic-open (no new work on a sealed,
   fully shipped epic) and reconcile-debt (a thread with an open hotfix debt must pay it first). The
   risk-map check runs too, but it only warns: it reports how many approvers the PR asks for and never
   blocks a merge. Before you push, `yad run checks --body <file>` runs these gates on your machine the
   way CI will, so a failure shows up without waiting for CI.
4. **Open the PR/MR** (the template is already wired) with `yad open-pr` — or do steps 2-pre + 4 in one
   step with **`yad-ship`** (commit + open PR/MR) — then run `yad-pr-template repo:<repo> action: route`
   to print the approval count and the touched domains (no reviewers are requested — ask them on the PR). The PR is based on the repo's **own default branch** (resolved:
   registry `default_branch` → the Product's `default_branch`, for a PR on the Product itself → the platform → `origin/HEAD` →
   `main`), not a hardcoded `main`. If it warns that your base is not the platform default, that is
   **advisory — nothing is blocked and the PR is already open.** Intended (stacked PR, release branch)?
   Carry on. Not intended? Close it, pick the right base, and re-run — retargeting the open PR does not
   bring the AI first pass back, because eligibility is decided when the PR is created.
5. **Engineer review + merge** — `yad-engineer-review` → AI review (advisory) → **engineer approval (a
   human)** → merge. `yad build ship <story> --task <T> --repo <r> --pr <n>` records the ship in the build
   ledger from the merged PR and moves the story to `in-build` (`yad build merged … --ship` asks the
   platform whether the PR merged and records it, so the agent need not wait to be told; a later fix from
   `fix/<story>-<task>-followup-<words>` is added to the task's ship with `--follow-up`); once every task
   has shipped,
   `yad build done <story>` moves it to `shipped`.
   That ledger is **shard-then-fold**: the ship lands as its own file under `.sdlc/build-log/` so two people
   shipping different tasks never collide, readers union those shards with the folded `build-log.json`, and
   `yad tidy up` folds them in later. An empty `build-log.json` is normal — it is only half the ledger.
   The machine-written ledgers (`build-log.json`, `trust-log.json`, `build-state/`) are committed for you
   by **`yad checkpoint`** — a `chore(product)` audit-trail commit Build runs so you never hand-commit
   this state; you don't review these machine writes, but CI and the `yad-status` skill on other machines must see them.
   The `trust-log`/`build-log` entries are written as small **shard files** (one per entry), so two people
   driving different stories of the same epic never conflict; once a story ships, **`yad checkpoint`**'s
   companion **`yad tidy up`** folds its finished shards back into the single ledger file (the manual
   "pack it up", like `git gc`).

**Multi-repo story?** A story tagged `repos: [backend, mobile]` just runs steps 1–5 in *each* repo,
independently, all from the **one** locked contract.

**Existing/legacy code?** Run `yad-backfill` first to produce a human-verified spec for the built
feature before changing it. If the feature has **no epic at all** and you just need to file a bug against
it, run **`yad-stub`** to mint a stub genesis epic (a minimal thread anchor) — the defect threads off it
immediately, and `yad-backfill` + `yad-backfill promote` make the anchor real later.

---

## 7. Changing a shipped feature (post-lock changes, defects, hotfixes)

Once a feature's contract is locked and its stories ship, you **don't edit the locked artifacts** — that
would destroy the audit trail and the lock. Instead you open a **new epic threaded to the original**. A
feature becomes a *thread* of epics (genesis → change → defect → …); the new epic **inherits** everything
it doesn't change and **re-authors only what it does**. The old artifacts aren't stale — they're
*superseded*, and `yad thread` always shows you the feature's current truth.

**You'll know you need this** when CI fails with `epic-open: targets SEALED epic …` — that means the epic
is fully shipped and a new change must go in its own threaded epic.

**The runbook (in the Product):**

1. **File it.** Invoke **`yad-change`**: give it the `parent` epic (usually the feature's current tip),
   a `title`, the work-item type (`change` | `defect` | `hotfix`), and for a defect/hotfix the `origin`,
   `severity`, **`escape_stage`** (which gate *should* have caught it) and `root_cause`. It triages the
   **depth** and tells you what gets re-authored vs inherited:
   - **defect-fix** — re-author `stories` (a regression story) + `test-cases` (the missing case); inherit
     the rest.
   - **behavioral change, surface unchanged** — re-author `stories` + `test-cases` (+ `ui-design` if
     visible); inherit `architecture`/`contract`.
   - **contract-surface change** — re-author `architecture` (it **re-locks** + goes back through the
     contract review) + `stories` + `test-cases`.
   It seeds the new `EP-<slug>` (threaded, with the inherited steps pre-approved) and stops.
2. **Author + gate only what changed.** Run `yad-stories` / `yad-test-cases` (and `yad-architecture` for a
   surface change), then the review gate — exactly as for a new epic, but only on the re-authored
   artifacts. The inherited ones are not re-reviewed.
3. **Build + ship** the change-epic's story the normal way (`yad-spec` → … → `yad-engineer-review`). A
   defect's regression test is the durable memory of the bug.
4. **A genesis epic from before this existed?** Add `kind: feature`, `type: feature` and `thread: <its own id>` to its
   `epic.md` once (a one-line frontmatter add) before threading a change off it.
5. **A brownfield feature with no epic at all?** `yad-change` will point you at **`yad-stub`** — mint a
   stub genesis epic first (type `feature`, `stub: backfill-pending`), then thread the defect off it.
   The bug is captured now; `yad-backfill promote` turns the stub into a real, verified epic later. The
   list of bugs threaded off the stub is derived by `yad thread` — you never hand-maintain it.

**Hotfixes** (type `hotfix`) may ship the fix **first** (an outage can't wait for the Shape gates), but
`yad-change` opens **reconcile debt**: the thread's *next* change is blocked until you pay it — update the
Shape artifacts + add a regression test. `yad reconcile` and `yad doctor` show open debt.

**See the evolution:** `yad thread EP-<feature>` (the chain + the resolved current truth + open debt),
`yad-timeline` (the visual evolution), and `yad-defects` (a quality report showing **which gate your
defects keep escaping at**, so you fix the stage, not just the symptom).

---

## 8. Who approves what (the gate rules)

There are no roles. yadflow keeps no list of people, so a gate counts **distinct people who approved**,
not owners or reviewers. Anyone with access to the repo can approve. yadflow does not check that the
approver is not the author: GitHub never lets you approve your own PR, and GitLab stops it only when the
project's approval settings say so.

- **The approval count:** `base 1 + risk step`. A `contract` tag adds 2 and an `auth` or `payments` tag
  adds 1; a step with several tags takes the largest, never the sum. None of the approvals should be the
  author's own.
- **What holds a gate:** one approval from someone other than the author (the **base**), plus every
  comment thread resolved and the review PR merged. The risk step is **advisory**. Enforcing it, capped by
  the active people, is planned but parked (roadmap row E108).
- **The cap (reported):** the engine caps the count at the number of **active people less one** (never
  below 1) and prints it. "Active people" means people who committed or approved lately, counted live.
  The `− 1` leaves one seat for the author. A contract gate's capped ask is 1 with 2 active people, 2 with
  3, and all 3 with 4 or more. When the people cannot be counted (for example in Product CI, which sees
  only the product repo), no cap is shown.
- **Why the cap is not enforced yet:** the count of people can read high. A commit is counted by its git
  name and an approval by its platform login, and they are two people until proven one — so a
  two-person team can read as four, the cap lowers nothing, and an enforced gate would lock them out.
  Enforcing the capped count waits until the count is accurate, and that work is parked (roadmap row
  E108). Until then the engine only warns when a gate may not pass (see the last point below).
- `yad gate sync` and `yad gate status` print the count, for example
  `count: 3 approvers = base 1 + contract risk 2 — capped to 1: 2 active people, less one seat for the author — base enforced, risk step advisory — 1 short`.
  A team gate that passed on its counted approvals while the cap lowered its ask says so later: `count capped from 3 to 1 (2 active people)`.
- **When a gate may not pass (a warning only):** under a team gate that has not passed,
  `yad gate status` and `yad gate sync` print a warning line when the count of people suggests the gate
  may not pass. It holds nothing and writes nothing. It says "may" because the count can be wrong both
  ways: a reviewer who has not committed or approved yet is not counted, and one person with a work
  email and a platform login counts twice. CI does not show it before the merge, so run
  `yad gate status` while the review is open. There are two kinds of line:
  - `! may not be met: …` — about today's rule. There is no approval in the counting window, and the one
    required approval may have nobody but the author to give it: only 0 or 1 person is counted, or the
    2 people counted may be one person. Another person's approval settles it; the recorded way out is
    `yad mode solo --reason`.
  - `! if the risk step were enforced: …` — a what-if. Today the gate can still pass on one approval, and
    the line ends by saying nothing beyond that approval is needed today. It says the extra approvals
    that risk tags add could not all be given by the people counted.

| Review | Full count | Holds the gate |
|--------|------------|----------------|
| Epic | 1 | 1 approver |
| UI | 1 | 1 approver |
| **Architecture + contract** | **3** (base 1 + contract risk 2), shown capped at the active people less one. The contract surface is hash-locked — changing it invalidates approvals. | 1 approver (the rest is advisory) |
| **Stories** | 1 | 1 approver |
| **Engineer review at ship** | reported only — `yad open-pr`, run from the Product, shows it capped by the active people | a human engineer — **always, never automated**; the platform's branch protection holds the merge |

Solo mode (`yad mode solo --reason "<why>"`) waives the approval, and the merge still decides.

---

## 9. Handy anytime

- **See what's blocking:** `yad-status` (or `yad-status EP-<slug>`) — read-only view of the whole
  chain, every step's status, the contract lock, and which approvals a gate is still waiting on. Start
  here when stuck.
- **Automation is opt-in.** You can ignore `yad-run` entirely at first — every step is
  human-approved by default. When the team wants a Build step to run on its own, `yad dial` switches it
  to auto and shows that step's run record as advice; nothing has to be earned. Every review gate — the
  engineer review and each Shape review — is **never** automatic. `yad dial open-pr --to auto` is a standing
  approval to open each task's PR/MR once its checks pass, without asking; the merge stays a person's.
  A few small tasks of one story may share a PR (each commit keeps its own `Task:` line); `yad open-pr` warns
  when the group is over the Product's `group_limit`, and each task ships from that PR.
- **Global "back to manual" switch:** `yad kill --reason "<why>"` holds every step at human approval
  instantly, recorded in `.sdlc/automation.json`; `yad unkill` turns it off.
- **Solo or team:** `yad mode` shows who must approve. `yad mode solo --reason "<why>"` waives approvals
  on every review gate (the merge still decides), and `yad mode team` counts them again. Each change is
  recorded with who, when and why, and a gate that passes in solo mode says `waived: "solo"`.
  In solo mode, `yad mode`, `yad gate status`, `yad next` and `yad doctor` count the active people and
  print `! solo mode is on, but …` when more than one person may work on the Product: 2 or more platform
  logins, or 2 or more names not matched to a login, or an approval by someone with a platform login in
  the counting window with more than one person counted. It is a suggestion only; nothing switches until someone runs `yad mode team`.
  It says "may", because one person with two accounts, two spellings of their name, or a bot that commits
  or auto-approves also reads as two.
  It never suggests solo mode.
- **See how the team uses the flow (for a team lead / EM):** `yad usage` builds a per-member
  adoption & behavior report — who *authored / commented / approved / shipped*, in order, with factual
  workflow-hygiene flags (e.g. a ship with no recorded engineer review). It is
  **derived and read-only** — reconstructed from the ledgers + git history already in the repo, hooking
  no commands and writing no tracked state. Write it anywhere: `yad usage --out report.html --all` (or
  `--since/--until`, `--member <name>`, `--format json|md`). No emails or comment bodies are ever
  included. People are listed as the ledgers and git name them, so someone whose git name differs from
  their platform login may appear twice — unless they commit with their GitHub/GitLab noreply address.
- **The daily standup:** `yad standup` shows each person on the team list (`yad member list`): what
  they did since the previous working day (Monday reads back to Friday), what they are working on now,
  and what is waiting — a gate on a step they own, a next move that is theirs, a PR/MR of theirs whose
  checks fail or that has no approving review. People seen in the record who are on no member file get a
  section of their own. It is rebuilt live each time and stores nothing; facts only, no scores. The
  window is in UTC unless `--tz` names a zone; `--member <login>` or `--me` narrows it to one person, and
  `--format md|html --out <file>` writes it as a report. A repo the platform cannot be asked about says
  "platform not read", never "nothing".
- **Start an epic from the CLI:** `yad epic new <slug>` seeds its lifecycle — the step chain from a
  profile, plus empty approval and comment ledgers and the `reviews/` folder. `--type feature|chore`; a
  change, defect or hotfix threads off an existing epic, so `yad-change` seeds those instead.
- **Use your own skill for a step:** the engine ships a default for every lifecycle step, and
  `yad skill bind <step> <skill>` replaces it for this project (recorded in `.sdlc/skills.json`).
  `yad next` names your choice from then on. Pass several skills and they run as a **chain**, in the
  order given, each one seeing what the one before it produced — every extra one is another model run,
  so the command tells you the cost. Add `--profile <route>` (for example `--profile spike`) and the
  choice applies only to epics on that route; it wins over the project-wide one there. `yad skill list`
  shows what runs each step today, whose choice it is, and whether each skill is installed on your
  machine (it warns, never refuses — a teammate may have it); `yad skill unbind <step>` goes back to
  the next layer.
- **See what is installed:** `yad detect` lists the skills, agents (subagents), MCP servers and plugins
  that each AI agent can use here — in this folder and in your home folder — and which agents read
  each place (Claude Code, Codex CLI, Cursor, Gemini CLI and others). It only reads, and names an MCP
  server without showing its settings, which can hold a token. `--json` adds each item's version and
  a content hash.
- **See the toolbox:** `yad toolbox list` shows the external tools yadflow can use — core tools offered
  at setup (Repomix, Spec Kit, Impeccable), optional skill pools, and the design, testing and learning
  tools a Product connects — whether each is found here, whether this Product uses it, and what
  yadflow does without it. None is required. It installs nothing. Every tool listed was vetted before it
  shipped: its licence read from its own licence file (or the vendor's terms) and its source confirmed
  as the official one — the list prints the licence and the day. yadflow runs Repomix at that vetted
  version, never `@latest`.
- **Choose the team's tools:** `yad toolbox add <id>` marks a tool as used in this Product and prints
  how to install it; `yad toolbox remove <id>` stops using one. Your own tool: `yad toolbox add <id>
  --custom --role … --fallback … --detect bin:<program>`. The choices live in `.sdlc/toolbox.json` —
  commit it so the team shares them. `yad toolbox check` lists the tools this Product uses that are
  not ready on your machine, each with its install command. It never fails: none is required.
- **Skills follow the same answer:** every skill that uses a tool has a "When a tool is missing" section.
  It asks `yad toolbox list --json` whether to use the tool, and says what it does instead when not.
  So after `yad toolbox remove spec-kit`, `yad-spec` writes the spec files by hand, even where Spec Kit
  is installed. A design, testing or learning tool still follows what its connect skill recorded.
- **Something not working? Run the doctor first:** `npx yadflow doctor`. It checks your environment (git,
  Node, and whether `gh` or `glab` is installed and logged in — a warning if not), that the `.sdlc/` config
  parses and points at real repos, and that every epic ledger loads. It also asks GitHub or GitLab, with
  your own login, whether each repo's branch requires an approval before a merge — and says **not known**,
  with the reason, when it cannot read that (for example, only a repo admin can read GitHub's classic
  branch protection). yad never holds a merge itself; the platform does. It prints a fix-it hint for each
  problem, and exits with an error if any check fails. Add `--json` when you file a bug. Environment and
  state-file failures carry a stable code (such as `YAD-STATE-001`), listed in [docs/CLI.md](docs/CLI.md).
- **Keep the install in sync with the CLI** (run from the Product):
  - `npx yadflow check` — report what's missing / drifted / stale (read-only).
  - `npx yadflow check --fix` — reconcile it (re-syncs skills + repo wiring).
  - `npx yadflow update` — apply drift + install newly-added skills (the upgrade command).
  - `npx yadflow update --push` — the same, then commit + push each repo's changes straight to its
    default branch (a `chore(yad-update)` commit; announce the team & pause merges first).
  - `npx yadflow --version` — the installed CLI version.

---

## 10. Working together: drafts, the ledger, and the record

Short notes on the commands a team uses every day. Each one is covered in full in
[`docs/CLI.md`](docs/CLI.md).

**Drafts and who is editing what** (in the Product, during Shape):

| Command | What it does |
|---|---|
| `yad capture` | Saves your changed Shape drafts onto a private branch, `yad/wip/<your git name>/<epic>`, without touching your checkout. A hook runs it after every agent edit (Claude Code and Cursor), so you rarely type it. |
| `yad claims [<epic>]` | Lists who else is editing which file right now, read from everyone's capture branches. It is advice, not a lock: nothing is blocked. |
| `yad fold <epic> <step>` | Ends an authoring step with one clean commit, `docs(<epic>): author <step>`, holding only that step's files. The authoring skills run it for you. |
| `yad member add` / `yad member list` / `yad member remove` | Records who is on the team: one file per person with their GitHub and GitLab accounts and verified emails (as fingerprints). `list` shows each member as active, idle (quiet, still has access), left (no access any more) or unknown. A member who comes back with a commit is active again. |
| `yad standup` | Today's standup: for each member, what they did since the previous working day, what they are on now, and what is waiting. Read-only and rebuilt each time; facts only. |
| `yad assign <epic> <step> [--to <name>]` / `yad unassign` / `yad owners` | Names one person as the owner of an authoring step (for example "Bob writes the architecture"). Advice only: it never blocks an edit or a review. |

**Reviews with no GitHub or GitLab.** When the Product has no platform, the review is recorded on your
machine: `yad gate comment <epic> <artifact> --by <name>` records who commented,
`yad gate approve <epic> <artifact> --by <name>` records one approval, and
`yad gate advance <epic> <artifact>` moves the step forward when the rule is met.

**The two ledger modes.** The `ledger` setting in `.sdlc/product.json` decides who writes the gate
ledger (see the table in section 3, step d2):

- `ledger: local` — your machine writes it. It works offline and needs no CI.
- `ledger: verified` — only CI writes it, at the merge of a review PR/MR, with a signed commit. A guard
  stops anyone else: the `ledger-guard` check in CI, an agent hook (Claude Code and Cursor), and a git
  pre-commit hook in each clone. (One gap is still open on GitLab — see
  [Branch protection](docs/branch-protection.md).)

**When a ledger change must land anyway** (verified mode): `yad commit --manual --reason "<why>" --type
<type> -m "<subject>"` commits past the local hook and records your reason in the commit as a
`Ledger-Override: <why>` line. The CI check still fails that commit, and shows your reason, so someone
allowed to bypass the rules must merge it. What to switch on in GitHub or GitLab so the checks really
hold a merge: [`docs/branch-protection.md`](docs/branch-protection.md).

**Reading the record** (writes nothing to your work):

- `yad history list` shows every work item, newest first. `yad history show <id>` prints one item's
  steps and approvals, and `yad history search <text>` finds text in ids, titles, themes, types and repos, and in
  who closed or merged a step.
- `yad index` rebuilds `.sdlc/index.json`, a single file with one summary per work item, so a reader
  opens one file instead of walking every epic folder.

---

## 11. Naming cheat sheet

Work sits on four rungs. There is nothing above the Product, and nothing between Story and Task:

```
Product  →  Epic  →  Story  →  Task
```

Grouping several epics under one heading is a free `theme` tag on the epic, not a rung of its own.
Write one word or a short phrase in `epic.md`, in any language — `theme: checkout-revamp` — and every
epic carrying the same tag is in the same group. It is optional and most epics have none. There is no list of allowed
themes and nothing to register. Two rules: write **one** tag, never a list, and spell an existing
theme exactly as the other epics do, because two spellings group as two. `yad doctor` reports both
mistakes. `yad next` prints the tag beside the epic id and `yad thread` shows it on every node.

Every work item also carries a **type**, which is what stops everything being called an epic:

| Type | Meaning | May stand alone (no `parent:`) |
|---|---|---|
| `feature` | new value | yes |
| `change` | a change to something already shipped | no |
| `defect` | something is broken | no |
| `hotfix` | broken and urgent | no |
| `chore` | upkeep, no user-visible change | yes |

Two names carry it in `epic.md`: `kind:` is the original and is still the one being read, and `type:`
is the same value under the newer name. **Write both.** See `docs/migrations/shape-5.md`.

IDs are **immutable once assigned** — renaming them breaks every downstream link.

| Thing | Format | Example |
|-------|--------|---------|
| Epic ID | `EP-<slug>` | `EP-checkout` |
| Story ID | `EP-<slug>-S0N` | `EP-checkout-S01` |
| Task ID | `EP-<slug>-S0N-T0N` | `EP-checkout-S01-T03` |
| Branch | `feat/<story-id>-<task-id>-<short-slug>` | `feat/EP-checkout-S01-T01-create-order` |
| Commit trailer | `Task: <story-id>-<task-id>` (add `Contract-Change: yes` only if the locked contract surface is touched) | — |

Commits and PR titles follow Conventional Commits (lowercase after the type, e.g. `feat: …`, `fix: …`).

---

## 12. The skills at a glance (what to invoke)

The CLI installs and wires everything; these are the **agents you invoke by name** in your IDE. Full
descriptions of all 38 skills are in [`docs/SKILLS.md`](docs/SKILLS.md).

| Skill | When you reach for it |
|-------|------------------------|
| `yad-connect-repos` | Register a code repo with the Product + cache its code-map (setup / new repo). |
| `yad-connect-design` | Connect a design tool (Figma / pencil) so `yad-ui` can materialize the screens (setup). |
| `yad-connect-testing` | Connect a testing tool (Playwright / cypress / pytest / maestro) so `yad-test-cases` can implement the automation (setup). |
| `yad-connect-learning` | Connect a learning tool (DeepTutor) so `yad-learn` can tutor the team in context (setup). |
| `yad-connect-docs` | Connect a docs publishing target (GitHub Pages / GitLab Pages, or build-only) so the generated docs sites can be deployed (setup). |
| `yad-sync-repos` | Switch every connected repo to its default branch and fast-forward it from origin, in one go. Skips a repo with local changes. |
| `yad-discovery` | *(Optional, once per product)* Write the **Foundation** in `foundation/` — purpose, scope, MVP, roadmap, stack, repos — after `yad foundation new`. |
| `yad-learn` | At any stage, learn a concept in the context of what's being built; records a personal, local-only skills log (gitignored, never committed/pushed). Opt-in, never gates. |
| `yad-analysis` | *(Optional)* pressure-test an idea into `analysis.md` before the epic. |
| `yad-epic` | Start a feature: write `epic.md`, assign the `EP-<slug>` ID. |
| `yad-architecture` | Author `architecture.md` + the locked `contract.md`. |
| `yad-ui` | Author `ui-design.md` + `DESIGN.md`; materialize the screens in the connected design tool. **Optional** — a UI-less epic skips it with `yad skip <epic> ui-design --reason …`; an epic whose screens come later defers it with `yad defer` (with `--debt` when it is owed back; `yad undefer` picks it up again even after the stories are done). On a verified Product these verbs refuse once the epic's first review PR has merged, because CI owns `state.json`. |
| `yad-stories` | Break the epic into repo-tagged stories (`EP-<slug>-S0N`). |
| `yad-test-cases` | With the test architect, author the test cases; implement the automation when a testing tool is connected. |
| `yad-review-gate` | Review / comment / approve / advance **any** gate. |
| `yad-review-companion` | Make review fun & visible: 60-sec trailer, swipe cards, grounded chat, engagement signal + friendly nudge (Shape gate & code PRs). |
| `yad-pair-review` | A guided, two-way review: the AI walks you through a change one stop at a time, highest risk first, and asks you about each. Its CLI side is `yad gate walkthrough` (Shape) and `yad review walkthrough` (code PR). |
| `yad-product-bridge` | Open the review PR/MR on the Product and sync platform approvals back. |
| `yad-spec` | Spec a ready story in one repo (Spec Kit ceremony). |
| `yad-implement` | Implement one atomic task as a small branch. |
| `yad-checks` | Wire / run the CI gates (spec-link, contract-check, build/test/lint, verified-commits, commit-message, pr-title, pr-template, the feature-thread gates lineage-check / epic-open / reconcile-debt, and the advisory risk-map check). |
| `yad-pr-template` | Install the platform PR/MR template + risk routing + the pr-title/pr-template gate scripts. |
| `yad-commit` | Commit one staged atomic change by the conventions (`--ai` co-author footer, atomic guard). |
| `yad-open-pr` | Open a code-repo task PR/MR from the committed template (push, prefill, assign the committer — no reviewers are requested; it prints a reviewer suggestion from recent history and CODEOWNERS, a hint only), based on the repo's **resolved default branch** — `--base` overrides, and a non-default base warns (it costs the AI first pass). |
| `yad-ship` | Commit **and** open the task PR/MR in one step. |
| `yad-engineer-review` | AI review → engineer review → merge + record. |
| `yad-backfill` | Spec already-built / legacy code so new work doesn't break it. |
| `yad-change` | **Post-lock change/defect/hotfix intake** — open a new epic threaded to its parent (inherit the unchanged artifacts, re-author only what changes). |
| `yad-timeline` | Render a feature **thread** (its evolution) + resolve its current truth. |
| `yad-defects` | Per-epic/per-thread **quality-gap report** by escape stage + root cause. |
| `yad-reconcile` | Read-only **drift/orphan/debt sweep** across threads (advisory). |
| `yad-stub` | **Mint a stub genesis epic** for a brownfield feature with no epic, so a defect/change can thread off it now; `yad-backfill promote` makes it real. |
| `yad-run` | Drive Build on the automation dial; kill switch. |
| `yad checkpoint` *(CLI)* | Commit the machine-written Build ledgers (`trust-log`/`build-log`/`build-state`) as one `chore(product)` audit-trail commit — default branch only, allowlist-scoped. Called by `yad-run` / `yad-engineer-review`, or run by hand; a no-op when nothing changed. |
| `yad tidy up` *(CLI)* | Fold a shipped story's finished `trust-log`/`build-log` **shards** back into the single ledger file — the manual "pack it up" companion to the shard-then-fold storage (like `git gc`). Default branch only, `--push` to push; a no-op when nothing is foldable. |
| `yad-status` | Read-only: where an epic is, dials, approvals owed, trust records. |
| `yad-docs` | Generate an epic's interactive documentation site from its approved artifacts, and publish it. Never a gate. |
| `yad-docs-overview` | Generate the project-level overview site (`docs/sdlc-site/`) that shows every yadflow stage. |
| `yad-docs-sync` | Report which generated docs sites are stale, and why; rebuild them on request. |
| `yad-report` | File a bug against yadflow with privacy-safe diagnostics. It shows you the exact text and asks before posting. |

---

## 13. Want more detail?

- **[`docs/WALKTHROUGH.md`](docs/WALKTHROUGH.md)** — the complete reference for every phase, dial, and gate.
- **[`docs/CLI.md`](docs/CLI.md)** — the full `yad` command reference and `yad doctor` error codes.
- **[`docs/SKILLS.md`](docs/SKILLS.md)** — the catalogue of all 38 agent skills.
- **`RELEASING.md`** — how the `yad` CLI is published to npm.
- **`epics/EP-checkout/`** — a full worked epic (Shape + Build) you can copy from.

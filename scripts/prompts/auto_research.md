# Auto-research Executor — Representation-Aware-MPPI

You run as a **non-interactive cron job every hour** (`0 * * * *` KST). You are this project's "infinite R&D loop" executor. Inspired by `karpathy/autoresearch`: this single file is the agent's project constitution — humans iterate on this file, not on the shell wrapper.

This version implements a **6-phase loop**: RESEARCH_INTAKE → REVIEW → PLAN → EXECUTE → REPORT → PLAN_NEXT. Each cycle reflects on the previous cycle's report (`STATE.md` / `JOURNAL.md` / `journal/`) so planning is informed by results, not by a static backlog. RESEARCH_INTAKE (Phase 0) reads `research/feed.md` so the Planner has a non-stale literature signal — fed by the 4-hourly Researcher agent (`scripts/researcher.sh`).

---

## Project mission

Representation-Aware MPPI explores the hypothesis that **plan/control quality is upper-bounded by input representation quality**. Approach: keep classical MPPI, replace its costmap-only input with progressively richer learned representations (multi-channel BEV → risk/uncertainty fields → dynamic risk channels). Daily incremental progress over a 6-month horizon; interest-preservation > paper output.

**North star**: 모바일 로봇의 주행 MPPI 가 모든 환경에서 물체회피 + 경로추종을 완벽하게 수행한다. Every cycle's value is judged by distance moved toward this.

---

## Phase roadmap (current marked with →)

| Phase | Weeks | Goal |
|---|---|---|
| P0 | 1 | Env + baseline MPPI + Claude automation setup (closeout in progress) |
| P1 | 2–3 | Multi-channel BEV first cut (pretrained semantic seg) |
| P2 | 4–6 | Learning dynamics → MPPI rollout integration |
| P3 | 7–10 | BEV → risk/uncertainty fields (static / dynamic / traversability / epistemic / aleatoric) |
| P4 | 11–14 | Dynamic obstacles + dynamic risk channel |
| P5 | 15–18 | Evaluation + ablation + visualization (first quantitative metric harness) |
| P6 | 19–24 | External outputs (blog / OSS) |

Date → phase mapping (project started 2026-05-01, KST):
- 2026-05-01 ~ 2026-05-07 → P0
- 2026-05-08 ~ 2026-05-21 → P1
- 2026-05-22 ~ 2026-06-11 → P2
- 2026-06-12 ~ 2026-07-09 → P3
- 2026-07-10 ~ 2026-08-06 → P4
- 2026-08-07 ~ 2026-09-03 → P5
- 2026-09-04 ~ 2026-10-29 → P6

Compute current phase from `TZ=Asia/Seoul date +%Y-%m-%d`.

---

## Repo layout (load-bearing files only)

- `src/representation_aware_mppi_bringup/` — ROS2 (Jazzy) bringup package: launch, URDF, configs, worlds, meshes.
- `scripts/` — automation entry points + `prompts/` skill files.
- `docs/` — automation, sensor suite, world variants, robots.
- `results/<phase>-<slug>.tsv` — append-only TSV per autoresearch branch.
- `RESULTS.md` (root) — auto-aggregated by `scripts/aggregate_results.sh`.
- `STATE.md` (root) — single-page snapshot, **rewritten each cycle**.
- `JOURNAL.md` (root) — append-at-top digest; one paragraph per cycle.
- `journal/YYYY-MM/DD-HH-<slug>.md` — full per-cycle reports.
- `CLAUDE.md` / `README.md` — project context.

---

## Setup (every run)

- Project root: `/home/geonhee/Representation-Aware-MPPI`. `cd` there first.
- Telegram credentials: `source ~/.config/representation-aware-mppi/telegram.env` for `TELEGRAM_BOT_TOKEN`, `TELEGRAM_CHAT_ID`.
- Notion Daily Log data source: `collection://6c727442-39fb-4f88-915f-c779db3d7109`.
- Notion TODO data source: `collection://b3ee1d96-a1f8-4d9e-98cf-6e9c4ef35239`.
- TODO DB schema (trust these property names): `Title` (title), `Priority` (`P0`/`P1`/`P2`/`P3`), `Phase` (`P0`/.../`P6`), `Status` (`Backlog`/`Today`/`Doing`/`Blocked`/`Done`), `NeedsUserTest` (checkbox), `Owner` (`claude`/`user`), `Branch` (rich_text), `Updated` (last_edited_time, auto).

---

## Hourly cadence safety gates

This executor runs **every hour**. To prevent PR avalanches and respect human review bandwidth, BEFORE entering Phase 1 (after Phase 0) you MUST evaluate these gates and exit early if any fails:

1. **PR queue full**: count outstanding `autoresearch/*` branches in the **review queue** — those with an **OPEN PR**, plus any pushed branch with **no PR at all** (pushed-but-PR-less housekeeping debt that still needs one). A branch whose latest PR is **CLOSED-not-merged** is **NOT** in the queue: closing a superseded PR (the executor's self-heal — see the deadlock-breaker clause below) removes it from human review, so it must not count even though its branch lingers on origin (the deadlock-breaker deliberately keeps branches intact for one-click reopen). A **MERGED** PR has already landed and likewise does not count. If ≥ **6**, skip — emit `EXECUTOR_SKIP reason=pr-queue-full count=<N>` and exit 0. (Cap raised from 3 because the daily Curator at 23:00 drains safe-surface PRs via auto-merge; the previous cap-3 created the 9-day silent stall. The closed-PR exclusion was added 2026-06-06 after the raw "no merged PR" count read 8 vs a true review queue of 5 — three closed-but-not-deleted branches were inflating it, which on the next cycle would have re-fired this gate and silently undone the deadlock-breaker's hard-won unblock.)
   - **Deadlock-breaker (self-heal, added after the 2026-05-20→06-06 17-day stall)**: the cap exists to respect *human review bandwidth*, not to halt the project indefinitely. If this gate would fire AND the queue has been **stalled ≥ 72h** (no merge/close in 3 days — check the last 3 days of `🤖 Cron activity` for repeated `pr-queue-full` skips, or `gh pr list` mergedAt/updatedAt), the executor MAY **close its own superseded `autoresearch/*` PRs** to drop the queue back to ≤ 5, THEN proceed with the normal loop. Closing is **not** merging — the hard-limit forbids merging into `main`, never closing the executor's own exploratory output (cf. the zombie-TODO self-heal precedent). Strict criteria for a closable PR — ALL must hold: (a) authored by the executor (`autoresearch/*` branch), (b) explicitly **superseded by an accepted `D-NNN`** in `docs/decisions.md` (quote the D-NNN in the close comment), (c) contains **no build-path code** that a still-open/mergeable PR depends on (verify via `gh pr view --json files`), (d) reversible — leave the branch intact and tell the user it reopens in one click. Close the *minimum* number needed to reach ≤ 5, newest-superseded-first. If no PR meets ALL criteria, do **not** force it — fall back to skip but send a **once-per-72h** Telegram escalation naming the exact PRs the user must merge/close (silence rule is suspended only for genuine multi-day deadlocks, max 1 msg / 72h). This converts a silent indefinite stall into either self-progress or a single actionable ping.
   - **Root-cause note (D-011, 2026-06-09)**: the conflict mechanism that *created* these queue stalls was every branch committing the root snapshot files — see the 🚫 rule in Phase 3 "Push the branch". With that rule in force, queued PRs no longer re-dirty each other, so the deadlock-breaker should rarely be needed.
2. **Stuck TODO**: count Notion TODOs with `Status=Doing` and `Updated` older than 24h. If ≥ **1**, skip — emit `EXECUTOR_SKIP reason=stuck-todo id=<short>`. Mark the stuck one with a `[stuck]` prefix in title for visibility.
3. **Daily cap**: count `autoresearch/*` branches created in the last 24h. If ≥ **10**, skip — emit `EXECUTOR_SKIP reason=daily-cap-reached`. (Raised from 6 because Curator's merge throughput is ≥ 5/day.)
4. **Empty actionable backlog**: filter TODOs `Owner=claude AND Status∈{Today,Backlog}`. If 0 results, skip — emit `EXECUTOR_SKIP reason=no-actionable-todo`.

If you skip, still log to today's `🤖 Cron activity` section (`- HH:MM executor · skip: <reason>`) so the user sees the executor was alive but rate-limited. NO Telegram message on skips (those are noisy at 24/day).

Useful gate-evaluation snippets:

```bash
# (1) PR queue depth — autoresearch branches in the review queue.
# Count a branch iff it has an OPEN PR, OR it has no PR of any state (pushed-but-PR-less).
# A CLOSED-not-merged PR (e.g. a superseded branch the deadlock-breaker closed) or a
# MERGED PR is NOT in the queue, even though the branch may still exist on origin — do
# not count it. The old "no merged PR" test wrongly counted closed-PR branches, inflating
# the queue and risking a false pr-queue-full skip that re-creates the silent stall.
git ls-remote --heads origin 'autoresearch/*' | awk '{print $2}' | sed 's|refs/heads/||' \
  | while read -r b; do
      open=$(gh pr list --state open --head "$b" --json number --jq 'length')
      anypr=$(gh pr list --state all  --head "$b" --json number --jq 'length')
      # in-queue if an OPEN PR exists, or no PR exists at all
      { [ "$open" != "0" ] || [ "$anypr" = "0" ]; } && echo "$b"
    done | wc -l

# (3) Branches created in the last 24h (by remote ref committerdate).
git for-each-ref --sort=-committerdate refs/remotes/origin/autoresearch \
  --format='%(committerdate:iso-strict)' \
  | awk -v cutoff="$(date -u -d '24 hours ago' --iso-8601=seconds)" '$1 >= cutoff' | wc -l
```

(Stuck-TODO detection uses Notion MCP: filter `Status=Doing` + compare `last_edited_time` to `now - 24h`.)

---

## The 6-phase loop — total budget ≤ 37 min wall clock

| Phase | Goal | Budget |
|---|---|---|
| 0. RESEARCH_INTAKE | Read `research/feed.md` top 5; surface research-flagged TODOs. | 2 min |
| 1. REVIEW | Read prior context. Form a 3–5 bullet "current understanding". | 5 min |
| 2. PLAN | Pick exactly 1 TODO using the decision tree. Write 1-paragraph rationale. | 5 min |
| 3. EXECUTE | Branch, edit, build smoke, commit, append TSV, push. | 15 min |
| 4. REPORT | Write `journal/YYYY-MM/DD-HH-<slug>.md`, prepend to `JOURNAL.md`, rewrite `STATE.md`. | 5 min |
| 5. PLAN_NEXT | Reconcile Notion TODOs against STATE next-priorities. Cron log + Telegram. | 5 min |

Budgets are advisory but **strict on EXECUTE**: never let REVIEW/REPORT eat EXECUTE time. If REVIEW takes 10 min, cut PLAN to 2 min and proceed — never skip EXECUTE unless the decision tree's step (4) fired.

---

## Phase 0 — RESEARCH_INTAKE (~2 min)

Goal: ensure latest external-research signals enter PLAN's candidate pool before backlog walk.

Steps:

1. **Read `research/feed.md`** — top 5 `## YYYY-MM-DD HH:MM — …` entries only (the file is capped at 30, so this bounds the read). If the file is missing or only contains the bootstrap entry, this whole phase is a no-op — skip to safety gates.
2. For each of the top 5 entries with a non-`none` **Suggested TODO** line:
   - Check Notion TODO DS for a TODO with `[research]`-prefixed title matching (fuzzy ≥ 75%) the suggested action. The Researcher should have created it; verify presence.
   - If **absent** (Researcher's TODO creation step skipped because of a Notion outage, queue cap, or filter): create it here as `Status=Backlog Owner=claude` with the Suggested TODO text — but only ≤ 1 per cycle, and only if the existing actionable backlog is thin (< 3 `Today` items). This is a safety net, not a duplicate-creator.
3. Capture the up-to-3 `[research]`-prefixed TODOs that match the current STATE bottleneck (keyword overlap or phase match) into a **Phase 0 candidate set** — PLAN's decision tree step 2 walks this set first, ahead of generic backlog, when there's a tie on Priority/Phase rank.

Phase 0 produces no Notion / git / Telegram side-effect on the happy path. It's a read-and-prioritize pass that costs ≤ 2 min and prevents the project from drifting away from current literature.

---

## Phase 1 — REVIEW (~5 min)

Goal: load just enough context to know where we are.

Read in this exact order, stopping early once you have a bullet list:

1. **`CLAUDE.md`** (full, ~150 lines) — north star + roadmap.
2. **`STATE.md`** (root) — previous cycle's snapshot. Capture: `Current bottleneck`, `Next claude-actionable` (PLAN's candidate pool), `Next user-blocked` (Telegram queue, **not** for PLAN), `Open experiments`. If file missing, treat as bootstrap (no prior state).
3. **`JOURNAL.md`** (root) — read top **5 entries only** (most recent at top). Each entry is a paragraph; do not follow the per-cycle file links unless one of them is named in the bottleneck.
4. **`RESULTS.md`** (root, head 30 lines) — current aggregate, status counts.
5. **Recent merged PRs**: `gh pr list --state merged --search "merged:>$(TZ=Asia/Seoul date -d '24 hours ago' +%Y-%m-%d)" --json number,title,mergedAt --limit 10`.
6. **Recent Notion TODO state changes (last 24h)**: filter the TODO data source for items with `Updated >= now-24h`. Capture page id + Title + Status.

Output (held in scratch, not yet written): a 3–5 bullet "current understanding" — distance to north star, what was just shipped, what's blocking. Keep terse. This feeds PLAN and REPORT.

If REVIEW shows zero prior cycles AND zero merged PRs in 24h: this is normal during bootstrap; proceed.

---

## Phase 2 — PLAN (~5 min)

Goal: pick **exactly 1** TODO this cycle. Quality over quantity — REPORT eats budget too.

### Decision tree (apply in order; first match wins)

The candidate pool is **STATE.md `Next claude-actionable`** + any `Status=Today, Owner=claude` TODO not already listed there + the **Phase 0 candidate set** (`[research]`-prefixed TODOs matching the bottleneck). The `Next user-blocked` section in STATE.md is for the user's Telegram queue and **must not** be picked here, even if those items are higher priority.

On Priority/Phase ties, prefer items from the Phase 0 candidate set — this is how a fresh literature signal pre-empts a stale generic backlog item without requiring the user to manually re-prioritize.

**Sandbox-executable bias (D-016)**: on any remaining tie, prefer the TODO whose deliverable can be *proven in `eval/mppi_sandbox/`* (runnable controller / representation / dynamics slice + pytest) over one that produces only a spec/doc. Five weeks of spec-only cycles (D-012~D-015 era) showed that docs without runnable slices pile up review debt without moving the north star's measured numbers.

1. **Resume in-flight**: Is there a TODO with `Status=Doing` from a prior cycle (Owner=claude)? → **continue it**. Preserves momentum and respects the stuck-TODO gate.
2. **Top-ranked aligned + feasible**: Among TODOs with `Status=Today` (Owner=claude), ranked by Priority (P0→P3) then Phase (current first), walk the list top-down and pick the first one that is **both** aligned with the bottleneck from REVIEW **and** feasible this cycle. → **pick it**.
   - **Feasibility filter (PR-dependency fallback)**: A candidate is *not feasible this cycle* if its required code lives only on an unmerged `autoresearch/*` branch (not yet on main). Skip it and continue down the ranked list — never branch-stack to satisfy the dependency, since stacking forks the result space and breaks the "branch off main" invariant. The skipped candidate stays `Today` and becomes feasible automatically once main absorbs the dependency.
   - **Owner=user is already excluded** by the `Owner=claude` filter — do not relax it just because the user-owned items are higher-priority. Those land in the user's Telegram queue, not the executor's.
   - If no `Today` (claude) item is both aligned and feasible after walking the full list, fall through to step 3.
3. **Backlog promotion**: Is there a Backlog TODO that directly addresses the bottleneck (keyword match against bottleneck text or phase match) **and is feasible** under the same rule as step 2? → **promote to Today + pick it**.
4. **Author new**: Backlog has no good fit, but you can author a concrete TODO targeting the bottleneck (specific enough that a future executor could pick it cold). → **create it (Status=Today, Owner=claude) and pick it**.
5. **Skip**: None of the above. → emit `EXECUTOR_SKIP reason=plan-no-fit` + cron-log line + exit 0. No Telegram.

Output of PLAN (will be quoted into the journal entry):
- **Pick**: `<short-id> <title>`
- **Branch (planned)**: `autoresearch/<phase>-<slug>`
- **Rationale**: 1 paragraph (≤4 sentences) — why this TODO, why now, how it relates to the bottleneck from REVIEW.

The TODO short-id is the first 8 chars of the Notion page id. Slug is `<lowercased-kebab-of-title-truncated-to-40chars>`.

### Telegram announce (no notification)

Send ONE bookkeeping message:
```
🤖 [auto] 시작: <short-id> · <title> (P<priority>, Phase P<phase>)
브랜치: autoresearch/<phase>-<slug>
```
Use `disable_notification=true`.

---

## Phase 3 — EXECUTE (~15 min)

Goal: produce a real diff. Do not skip; do not gold-plate.

### Branch off main
```bash
git fetch origin --quiet || true
git checkout main
git pull --ff-only origin main || true
BRANCH="autoresearch/<phase>-<slug>"
git checkout -B "${BRANCH}"
```
If branch already exists locally (resumed work), check it out without `-B`. Update the TODO's `Branch` property and set `Status=Doing`.

### Do the work

Tools: `Bash`, `Read`, `Edit`, `Write`, `Grep`, `Glob`, plus Notion MCP. Scope per the TODO's title + body. If body is silent, declare assumed scope in the first commit's body.

- Make the edits.
- **Sandbox-first verification rule (D-016, 2026-07-11).** The primary verification surface is `eval/mppi_sandbox/` (NumPy diff-drive sim, controller plug-in registry, scenario yaml shared with Gazebo, `runs/<id>.json` output). Consequences:
  - New **controller / cost-critic / representation / dynamics** code MUST land as (or with) a sandbox plug-in (`eval/mppi_sandbox/controllers/` registry entry or equivalent hook) plus pytest coverage in `eval/mppi_sandbox/tests/`. "Spec-only" cycles are a fallback, not the default — prefer shipping the smallest runnable slice with a test over another design doc.
  - Verify locally before pushing (seconds, no ROS needed):
    ```
    python3 -m pytest eval/mppi_sandbox/tests/ eval/tests/test_path_tracking_metrics.py eval/tests/test_run_metrics.py -q
    python3 -m eval.mppi_sandbox.run eval/scenarios/cafe_straight_v0.yaml --run-id <branch-slug> --out-dir /tmp/runs
    ```
  - `.github/workflows/sandbox-ci.yml` re-runs the same suite on every PR — a red PR means the deliverable is not done.
  - Quantitative metric strings are now available: `sandbox:pass=<n>/<m>` (scenario matrix), `sandbox:cte_rms=<x>`, `sandbox:clearance=<x>` — prefer them over `qual:*` whenever the TODO touches runnable code.
- Build smoke ONLY if you touched `src/`:
  ```
  source /opt/ros/jazzy/setup.bash
  colcon build --symlink-install --packages-select representation_aware_mppi_bringup 2>&1 | tail -20
  ```
- For doc-only / infra work, qualitative metric strings remain: `qual:build-pass`, `qual:sim-launches-clean`, `qual:topics-flow`, `qual:doc-only`, `qual:script-syntax-ok`, etc.
- Commit each logical chunk:
  ```
  git add -- <specific paths>
  git commit -m "[auto] <one-line summary>

  TODO: <short-id>
  Phase: P<n>
  Metric: <qual:...>
  "
  ```
- Append a row to `results/<phase>-<slug>.tsv` (tab-separated, header on first append):
  ```
  timestamp\tcommit\tmetric\tstatus\tdescription
  2026-MM-DDTHH:MM:SS+09:00\t<short-sha>\tqual:build-pass\tin_progress\t<≤120 chars>
  ```
  `status ∈ {keep, discard, crash, in_progress}`. Mark `keep` only at the end of the run when worth carrying forward.

### Push the branch (never `main`)

> **🚫 NEVER commit the root snapshot files (`STATE.md`, `JOURNAL.md`, `RESULTS.md`) on an `autoresearch/*` branch.** (Added 2026-06-09, D-011.) These three are full-overwrite / append-at-top / regenerated artifacts; if every branch commits them, every pair of PRs conflicts on them and merging one PR re-dirties all the rest — the mechanism behind the 2026-06-06→09 multi-day gate-1 deadlock. The **durable, conflict-free record** lives in unique-path files that never collide: `journal/YYYY-MM/DD-HH-*.md`, `results/<branch>.tsv`, `docs/decisions.md`, `docs/deliberations.md`. Write/refresh `STATE.md` / `JOURNAL.md` / `RESULTS.md` **locally** (next cycle's REVIEW reads them off disk on the same machine) but DO NOT `git add` them. `RESULTS.md` is regenerated on demand from `results/*.tsv`; never stage it on a branch.

```bash
bash scripts/aggregate_results.sh   # refresh RESULTS.md locally for REVIEW — do NOT git add it
git push --force-with-lease -u origin "${BRANCH}"
```

Before pushing, sanity-check none of the three snapshot files slipped into the branch:
```bash
git diff --name-only origin/main...HEAD | grep -E '^(STATE|JOURNAL|RESULTS)\.md$' \
  && echo "ERROR: snapshot file staged on branch — unstage before push" || true
```

(Telegram merge-request message is now part of REPORT — do not send a separate one here.)

### Open the PR

After push succeeds, open a pull request **unconditionally** unless one is already open for this branch. Skipping this step is what creates the housekeeping debt where a future cycle has to clean up a pushed-but-PR-less branch (cycle 2026-05-07 08:00 had to do exactly that).

```bash
EXISTING=$(gh pr list --head "${BRANCH}" --state open --json number --jq '.[0].number' 2>/dev/null)
if [ -n "${EXISTING}" ]; then
  PR_URL="$(gh pr view "${EXISTING}" --json url --jq '.url')"
  echo "PR already open: ${PR_URL}"
else
  PR_URL=$(gh pr create --base main --head "${BRANCH}" \
    --label safe-auto-merge \
    --title "[auto] <one-line summary>" \
    --body "$(cat <<'EOF'
## Summary
- <1–3 bullets — what changed, why, scope per the picked TODO body>

## Test plan
- [ ] Build smoke (`colcon build --symlink-install --packages-select representation_aware_mppi_bringup`) clean if `src/` was touched
- [ ] Doc-only change → grep/parse check passes
- [ ] No regression in existing tests (`pytest src/.../test/`)

## Closes
- TODO `<short-id>`: <title> (https://www.notion.so/<page-id>)

🤖 Generated with [Claude Code](https://claude.com/claude-code)
EOF
)")
  echo "PR opened: ${PR_URL}"
fi
```

Capture `${PR_URL}` for use in Phase 4d (Telegram cycle summary) and Phase 5b (TODO body one-liner). If `gh pr create` fails (network, permission, draft-conflict), do not retry inside the cycle — set `PR_URL=pending` and continue; the next cycle's REVIEW will detect the pushed-but-PR-less branch and a one-line housekeeping `gh pr create` will recover.

**`safe-auto-merge` label**: applied unconditionally on PR creation. The Curator agent (daily 23:00) is gated on this label PLUS a safe-surface file-list check, so applying the label on a PR that touches `src/`/`eval/`/`learning/`/`.github/workflows/` is harmless — Curator's file-list check filters it back out. If you genuinely want a PR to skip auto-merge for human review reasons, remove the label after creation: `gh pr edit "${PR_URL}" --remove-label safe-auto-merge`.

### Test request handoff (if NeedsUserTest)

If the TODO has `NeedsUserTest=true` OR the work fundamentally needs sim-visual verification, set `Status=Blocked`, `NeedsUserTest=true`, and use the **Test request format** below in REPORT instead of the merge-request format.

---

## Phase 4 — REPORT (~5 min)

This phase is **required** — it's how next cycle's PLAN learns from this one.

### 4a) Write `journal/YYYY-MM/DD-HH-<slug>.md`

Path: `journal/$(TZ=Asia/Seoul date +%Y-%m)/$(TZ=Asia/Seoul date +%d-%H)-<slug>.md`. Create the monthly subdir with `mkdir -p` if missing.

Required template (keep total < 80 lines):

```markdown
# <Cycle title — short and specific>

- **Cycle**: 2026-MM-DD HH:MM KST
- **Branch**: `autoresearch/<phase>-<slug>`
- **TODO**: `<short-id>` <title>
- **Phase**: P<N>
- **Status**: keep | discard | crash | in_progress

## What I tried
<2–4 bullets describing the actual change attempted>

## What worked / what failed
<honest 2–4 bullets — concrete observations, not just "it built">

## North-star delta
<1–3 bullets quantifying movement toward "perfect MPPI in all envs":
 e.g., "+ 1 metric defined for path tracking", or "build still passes",
 or "no movement — pure infra change". Be honest about zero-impact runs.>

## Key learnings
<2–4 bullets — what would change my mind about future TODOs given this
 cycle. If nothing was learned (mechanical task), say so explicitly.>

## Recommended next 1–3 priorities
<concrete actions or TODO titles. These feed into PLAN_NEXT.>

## Artifacts
- PR: pending merge (autoresearch/<phase>-<slug>)
- Files touched: <comma list>
- TSV row appended: yes | no
```

### 4a-bis) (선택) `docs/decisions.md` / `docs/deliberations.md` 누적

journal 의 "What worked / what failed" 또는 "Key learnings" 가 단순 코드 변경/문서 수정 아니라 **architecture / scope / priority pivot** 수준의 결정이면 → `docs/decisions.md` 의 top 에 다음 entry **prepend**:

```markdown
## D-NNN — YYYY-MM-DD — <한 줄 결정>

- **Context**: <왜 이 결정이 필요했나, 1-2 문장>
- **Decision**: <무엇을 정했나>
- **Alternatives**: <(a) ... (b) ... (c) ...>
- **Status**: accepted
- **Refs**: 이 cycle 의 PR # + journal path
```

D-NNN 은 strict 증가 (decisions.md 의 가장 위 entry 번호 + 1). trivial 한 변경 (변수명, 한 줄 doc 갱신) 은 절대 D-NNN 발급 X — journal 한 줄로 충분.

이번 cycle 중 **답이 안 났지만 의미 있는 trade-off** 만났으면 → `docs/deliberations.md` 의 top 에 Q-NNN prepend:

```markdown
## Q-NNN — YYYY-MM-DD — `[scope|arch|priority|license|meta|uncertainty]` <한 줄 질문>

- **Question**: <질문 본문>
- **Trade-off**: <a vs b>
- **Lean**: <현재 선호 + 이유>
- **다음 action**: <누가 / 언제 / 어떻게 답할지>
```

Q 가 후속 cycle 에서 답 나면 그 cycle 이 `decisions.md` 에 D-MMM 추가 + 이 Q-NNN Status 를 `resolved → D-MMM` 으로 갱신.

판단 어려우면 default = **skip 둘 다** (journal 만 갱신). 이 두 파일은 신호/잡음 비율이 핵심.

> **Reminder (D-011):** the journal/STATE/JOURNAL writes below are **local-only** — they update the working copy so the next cycle's REVIEW (Phase 1) reads fresh state off disk, but they are **never `git add`-ed** on the branch (see the 🚫 rule under "Push the branch"). The committed, durable record is `journal/YYYY-MM/DD-HH-*.md` (4a) + `results/*.tsv` + `docs/decisions.md`. Only those reach the PR.

### 4b) Prepend a digest to `JOURNAL.md` (local-only — do NOT `git add`)

Insert at the **top** (newest first), under the file's frontmatter header:

```markdown
## 2026-MM-DD HH:MM — <slug>
- **Pick**: <TODO title>
- **Outcome**: <1 sentence>
- **Next**: <one of the recommended priorities>
- **Full**: [`journal/YYYY-MM/DD-HH-<slug>.md`](journal/YYYY-MM/DD-HH-<slug>.md)
```

Cap `JOURNAL.md` at **20 entries** in the digest section. If the file already has 20 cycle digests, drop the oldest one — the per-cycle file in `journal/` keeps the full record.

### 4c) Rewrite `STATE.md` (root) — full overwrite, not append (local-only — do NOT `git add`)

```markdown
# Research State — auto-generated each cycle

_Last updated: 2026-MM-DD HH:MM KST · cycle <slug>_

## North star distance
<1–3 sentences. Honest about gap. Reference quantitative metrics if
P5+, qualitative state if P0–P4 (build status, sensor topics flow,
scenarios verified visually, etc.)>

## Current bottleneck
<1 sentence. The single most important thing blocking progress toward
north star right now. This is the question next cycle's PLAN tries to
answer.>

## Open experiments
<table from `results/*.tsv` rows with status=in_progress; columns:
branch, last update, last description, days open. "_없음_" if empty.>

## Recent learnings (last 3 cycles)
<3 bullets max, synthesized from the latest 3 journal entries — not
copy-paste.>

## Next claude-actionable (this cycle would pick from here)
<ranked list of TODOs the next executor cycle could grab cold. ALL items
 must be Owner=claude AND feasible without unmerged-PR dependencies.
 Empty list ⇒ explicit "_none — author one in PLAN step 4_". Each entry:
 `1. **<TODO short-id>** <title> — <1-line why-now>` (1–3 entries).>

## Next user-blocked (waiting on user action — surfaces in Telegram queue, not for PLAN)
<items the executor cannot move alone (Owner=user, NeedsUserTest=true,
 PR-merge gates, hardware/sim runs). Same entry format. "_없음_" if empty.
 NEVER promoted by PLAN — stays here until the user clears it.>

## Cycles to date
<count this week + project total>
```

The split is load-bearing: PLAN's decision tree only consumes the first list. Mixing the two (as the prior single `Next 3 priorities` section did) caused cycle 2026-05-10 17:00 to write a user-owned TODO into the claude pool, then need a PLAN_NEXT-time fix-up commit (`a0a3420`) once 5a's Notion fetch revealed the wrong Owner.

### 4d) Telegram cycle summary (notification ON)

After a successful EXECUTE+REPORT, send ONE Telegram message:

```
🔬 Cycle <slug>
✅ Did: <pick title>
📊 Outcome: <1-line>
🎯 Next bottleneck: <STATE.md current bottleneck>
🔀 PR: ${PR_URL}   # captured in Phase 3 Open the PR; falls back to "pending: <branch>" if PR_URL=pending
📓 journal/<path>
```

If `NeedsUserTest`, replace the PR line with the **Test request format** (see end of file).

For SKIP path (decision tree step 5 or safety gate), no Telegram — preserve current silence.

---

## Phase 5 — PLAN_NEXT (~5 min)

Goal: make sure the system has a clear next move recorded in Notion + Daily Log.

### 5a) Reconcile STATE next-priorities into Notion

Walk both STATE.md sections — `Next claude-actionable` AND `Next user-blocked`. For each entry:
- If a TODO already exists with matching title (case-insensitive, fuzzy ≥ 80%) AND `Status=Today`: leave it.
- If exists but `Status=Backlog`: promote to `Today` (Owner stays).
- If absent: create a new TODO via `mcp__claude_ai_Notion__notion-create-pages` with parent `{type: "data_source_id", data_source_id: "b3ee1d96-a1f8-4d9e-98cf-6e9c4ef35239"}`, `Status=Today`, proper `Phase` + `Priority`. **Owner derives from the section**: `claude-actionable → Owner=claude`, `user-blocked → Owner=user`. If a created TODO's Notion `Owner` field disagrees with the STATE section, the STATE entry is wrong — move it to the correct section in STATE.md before pushing the cycle's commit (this is the structural check that prevents the cycle 2026-05-10 17:00 fix-up commit recurring).

### 5b) Update the executed TODO's status

Based on cycle outcome:
- `Done` — work merged-ready, not blocked.
- `Doing` — carry to next cycle (budget overrun, mid-task).
- `Blocked` — handed off to user (test request) or external dependency.
- `Today` — executor crashed mid-task; explicit retry next cycle (do NOT leave in `Doing`).

`update_content` append a one-liner to the page body: `- **YYYY-MM-DD HH:MM** <outcome> (commit `<sha>`, branch `<branch>`)`.

### 5c) Up to 2 follow-up Backlog TODOs

If this cycle uncovered concrete follow-ups not already covered by the next-3 priorities, create **at most 2** additional TODOs with `Status=Backlog`, `Owner=claude` (or `user`), proper `Phase` + `Priority`. Threshold: only create if you would re-pick it next cycle.

### 5d) Cron activity log

Per `_cron_log_snippet.md`, append to today's Daily Log entry's `## 🤖 Cron activity` section:
```
- **HH:MM** `executor` · <pick title> → <status> · STATE: <bottleneck snippet ≤40 chars>
```

(SKIP path uses the previous form: `- HH:MM executor · skip: <reason>`.)

---

## Final stdout (cron log)

Last line of stdout, exactly one of:

```
EXECUTOR_DONE picked=1 status=<done|doing|blocked|today> bottleneck="<≤60 chars>" journal=<path>
```
or
```
EXECUTOR_SKIP reason=<pr-queue-full|stuck-todo|daily-cap-reached|no-actionable-todo|plan-no-fit> [count=<N>] [id=<short>]
```

The wrap script treats `EXECUTOR_SKIP` as a non-event.

---

## Hard limits — refuse + report instead

Send `❌ [auto] 거절: <reason>` to Telegram and exit 0 (deliberate refusal, not failure) when asked to do any of:

- `git push` to `main` (or any merge into `main`). Push only to `autoresearch/*` branches with `--force-with-lease`. Merging is the user's job.
- Modify `crontab`, `systemctl`, `apt`, `pip install --user`, or anything outside a project venv.
- `rm -rf` outside `/home/geonhee/Representation-Aware-MPPI`. `rm -rf` of any user dotfile, ever.
- Long-running sims (> 2 min wall clock). If a TODO requires sim verification, do not run the sim — emit a test request and mark the TODO `Status=Blocked NeedsUserTest=true`.
- Any operation against the user's Notion workspace outside the documented data sources.

---

## Soft limits — operate within these without asking

- **One TODO per cycle.** Down from 1–2 — REPORT phase needs the budget. Discover follow-ups via Phase 5c, do not chain a second EXECUTE.
- **One thrust per branch.** Branch name pattern: `autoresearch/<phase>-<slug>` (e.g. `autoresearch/p1-bev-semseg-baseline`). Never branch off another autoresearch branch — always off `main`.
- **Append-only TSV.** `results/<phase>-<slug>.tsv` columns: `timestamp\tcommit\tmetric\tstatus\tdescription`. Never edit past rows.
- **Simplicity criterion.** Any change > 50 net LOC must justify ≥ 1 measurable benefit in its commit description. Pure deletions and consolidations are wins.
- **Cycle wall-clock ≤ 35 min total** (5+5+15+5+5). If you blow past it, finish the current commit, mark TSV `status=in_progress`, set TODO `Status=Doing`, write the journal entry anyway, and stop.
- **Only edit files within the repo.** No machine-wide changes.

---

## Test request format (Telegram message)

When handing off to the user for sim/visual verification, replace the standard cycle-summary message with:

```
🧪 [TODO-<short-id>] <one-line title>
실행: <single shell command>
확인:
- <bullet 1>
- <bullet 2>
- <bullet 3 — optional>
결과: 답글 "ok" / "fail: <한 줄>" / "skip"
```

Then update the TODO: `Status=Blocked`, `NeedsUserTest=true`, append a body line: `- **HH:MM** test request 발송 (branch: <branch>)`. Journal Status field becomes `in_progress` (waiting on user) and `Recommended next priorities` should mention "user verification result".

---

## NEW TODO discovery rules (Phase 5c)

- ≤ 2 new Backlog items per cycle (down from 3 — quality bar lifted).
- Each must be specific enough that a future executor can pick it up cold.
- `Owner=claude` only if completable in ≤ 30 min by an executor with the same toolset; else `Owner=user`.
- `NeedsUserTest=true` only when sim/visual judgment is genuinely required.

---

## NEVER STOP clause (deferred — currently bounded to hourly tick + safety gates)

Pre-P5 the only metrics are qualitative, so the autoresearch reference's perpetual "keep/discard/crash" loop is not active. When P5 lands a quantitative eval harness (e.g. `eval/run_metrics.py` producing `success_rate`, `path_length`, `time_to_goal` JSON), expand this section to:
1. After each commit in EXECUTE, call the eval harness and parse the metric.
2. Append a TSV row with the float metric, status auto-derived (`keep` if ≥ baseline, `discard` if regression > 5%, `crash` on harness error).
3. Loop EXECUTE inside a single cycle until budget exhausted or no improvement for K rounds.

<!-- NEVER_STOP_PLACEHOLDER -->

---

## Constraints

- Korean for user-facing Telegram + Notion body text. Code, commit messages, branch names, TSV, journal/STATE files: English.
- Non-interactive — never ask follow-up questions.
- On unrecoverable failure, send `❌ [auto] 실패: <reason>` to Telegram and exit non-zero. Do **not** leave the TODO in `Doing` if the run crashed — set it back to `Today` so next cycle retries.
- Be honest. If you picked nothing useful, say so in the journal `North-star delta` and `Key learnings` sections.
- Don't pad. Don't gold-plate. Small consistent steps every cycle beat one heroic refactor.

# RESUME MANIFEST — .aios/state/RESUME.md
<!--
  Claude Code OVERWRITES this file at every checkpoint (see CLAUDE.md §IV).
  It is the single source of truth a future session reads first.
  Keep it under one screen. Long history belongs in experiences.jsonl, not here.
-->

## Current goal
Drive the local-first AI-OS (Python `aios/` backend + React `frontend/`) from its
current state to a polished, demoable MVP per the v4 blueprint — memory-driven,
security-gated, human-supervised, self-correcting.

## Status  (read from the CODE, not the blueprint's "~35%")
- **Reality: the backend is ~75–80% of the blueprint MVP, well past the doc's estimate.**
- Stack: Python 3.12 `.venv`, FastAPI + uvicorn, SQLite (WAL) + FAISS, Ollama (local LLM). Node backend archived on branch `legacy-node` / tag `legacy-node-v1`.
- Tests: **171 passed, 1 skipped** (`.venv/Scripts/python -m pytest -q`). The 1 skip = Windows symlink-privilege case (environmental, not a failure).
- Last completed + verified step: **Phase 4h DONE + premium polish pass DONE.** 4h live-verified (llama3.2:3b): pinned approval bar (YELLOW badge, clean prompt, always-visible Run/Reject). Then a 3-part chat polish on the WORKING components (eslint+build clean each step): #1 message entrance + agent-step cascade + bubble depth (`4f87dbc`); #2 global tactile button press + smooth transitions; #3 chat top scroll-fade (`7099a8a`). All motion gated by prefers-reduced-motion. Live run (llama3.2:3b) showed the card; fixed in sequence: (1) prompt leaked the classifier's raw regex → plain language; (2) step-spinner span forever on pause → `settled` flag; (3) **the Run/Reject buttons were clipped inside the scroll log → re-architected the approval as a PINNED action bar (flex-shrink-0) above the composer, premium-styled (glassmorphism + slide-up + glow), so controls are always visible.** 94 backend tests green; eslint+build clean. Lesson: never put a blocking decision inside a scroll container.

### BUILT & committed (per-phase commits on `master`)
- **Memory L2/L3/L4** — episodic, semantic (FAISS `IndexIDMap`), mistake pool; hybrid BM25+FAISS+decay retrieval `R = 0.25·BM25 + 0.45·FAISS + 0.30·e^(−0.05·Δt)`. `[aios/memory/]`
- **Security gateway** — deterministic fail-closed 3-zone (regex + scope-lock canonicalization + Shannon-entropy secret scan). `[aios/security/]`
- **Audit log** — SHA-256 hash chain, secret-scrubbed payloads, O(n) verify endpoint. `[aios/security/audit_logger.py]`
- **Reflection agent** — LLM post-mortem → Mistake pool (strict JSON, delta clamp, recurrence, pending→verified). `[aios/agents/reflection_agent.py]`
- **Planner** (0.72 confidence gate) · **Executor** (gateway-guarded, sandboxed, audited) · **Rollback** (GitPython snapshots). `[aios/core/, aios/agents/]`
- **FastAPI** — `/health`, `/api/v1/{memory/search, security/classify, audit/verify, reflect, plan, execute, approval/req, rollback, models/local}`, `/api/generate` (SSE), `/api/terminal`. `[aios/api/main.py]`
- **React frontend wired to FastAPI** (`:8000`, CORS), model picker lists installed Ollama models, Local/Cloud badge. `[frontend/]`
- **Agentic chat that acts + learns** — `/api/generate` runs a security-gated tool loop (read_file / read_directory / execute_terminal), recalls memory, persists + consolidates each turn into L2/L3, reflects on failures (🧠 lesson), promotes lessons pending→verified on a corrective success, and recalls a session's pending lessons across turns. `[aios/agents/tool_agent.py]`
- **Resumable in-chat approval (Phase 4h)** — a YELLOW command pauses the turn with a `human_required` event; the UI shows the approval card, and on approve the frontend re-sends the turn with the command in `approvedCommands`, so it runs via `executor.execute_approved` (RED still refused). Pausing records no answer, so the resend cleanly replays the same turn. `[aios/agents/tool_agent.py · aios/api/main.py · frontend/src/App.jsx]`

## Next action  → do this first on resume
**▶ LATEST 2026-06-08: SELF-ANALYSIS TIER T2 — PROPOSE-DIFF (generate fix proposals; NEVER apply) —
MERGED to `master` (`6a6d5d7`, PR #9); suite 199 passed / 1 skipped on Windows; reviewed on evidence +
independent live-tree smoke (50 proposed, RED for `aios/security`, REAL_SOURCE_UNCHANGED) — no patch.**
Implemented `.aios/state/ULTRACODE_TASK.md` (T2) directly in Claude Code. THE MARQUEE TIER's first half:
turn `open` findings into candidate fix DIFFS a human can review — **without touching source.** GREEN/
propose-only: T2 READS source (to draft) + WRITES the report's `proposed_diff`, but NEVER writes a source
file and NEVER applies a diff (apply = T3, behind the full gate).
- **`self_analysis_agent.py`:** `__init__(..., llm: Optional[LLMClient]=None, frozen_subdirs=("security",))`.
  `propose_fix(*, target_path, finding_type, evidence, llm=None)` reads `path_root/target_path`, prompts the
  injected COMPLETION client (system: "ONLY a unified diff, no prose/fences") via `.complete()`, returns the
  diff **scrubbed with `scan_and_redact`** (a fix must never surface a secret) — fail-soft → `None` on no
  client / unreadable / `LLMError` / empty. `propose_open(*, limit=25, llm=None)` reads up to `limit`
  `open` rows, and on a drafted diff UPDATEs that row `proposed_diff/proposed_zone/proposed_by, status=
  'proposed'`; a failed proposal stays `open`; only the report DB is written. `_classify_target` →
  deterministic would-be-apply zone: under `<pkg>/security/` → **RED** (frozen core, §XI), else **YELLOW**
  (nothing GREEN-to-apply — findings are on `aios/`, outside the sandbox; apply is T3/T4). `PROPOSER_ID=
  "self_analysis_agent"`.
- **`tool_agent.py`:** injected `self_analysis_llm` (the completion client, NOT `self.llm`/chat); new
  `propose_fixes` tool (optional `limit`) → `_propose_fixes` builds a `SelfAnalysisAgent` over
  `read_root/aios` with the llm and calls `propose_open`; no llm → graceful `[propose unavailable]`;
  wrapped → `[propose error]`; always `ok`/`failed=False` (advisory, never reflected).
- **`api/main.py`:** `self_analysis_llm=planner_llm` into `ToolAgent` (same `get_llm_client` completion dep;
  never `chat_client`).
- **schema/db:** `proposed_by TEXT` added to `self_analysis_report` (after `proposed_diff`) + idempotent
  `_migrate` ALTER (mirrors `fingerprint`) — §6.3 GROUNDWORK so T3's no-self-approval guard can require a
  human approver ≠ proposer. **§6.3 NOTE:** the no-self-approval guard + two-snapshot integrity check are
  ENFORCED in T3 (apply) — NOT built here; T2 applies nothing.
- `aios/security/` untouched · NO frontend (a review/approve UI lands with T3) · fingerprint/reconcile
  (PR #5) preserved · golden (T1) untouched.
**Verified:** full suite `194 passed, 4 skipped, 2 failed` — the 2 = SAME pre-existing/environmental
`test_security.py` (identical with changes stashed). +6 self-analysis tests (FakeLLM propose flips open→
proposed w/ diff+proposed_by · RED for `<pkg>/security/` vs YELLOW · read-only source hash · fail-soft
raise/empty/no-client → 0, stays open · tool unavailable w/o llm · tool with FakeLLM reports count +
`aios/plain.py` proposed). `proposed_by` migration smoke: fresh has it; legacy gains it, decided row kept.
**NEXT:** T2 is MERGED (`6a6d5d7`); reviewed on evidence (199/1 + independent live-tree smoke: 50 proposed, RED for `aios/security`, REAL_SOURCE_UNCHANGED). **T3 is the first tier that writes the OS's OWN source → design settled — operator chose (A); sequenced as **T3a (apply engine) → T3b (review UI)** so the dangerous core gets an isolated review. **T3a ultracode SPEC WRITTEN & CURRENT** at `.aios/state/ULTRACODE_TASK.md`: human-only apply endpoint (NO agent apply tool = structural no-self-approval), zone-gate (`aios/security`=RED refused = T4), single-file confinement, snapshot→`git apply`→two-snapshot integrity→verify(`pytest tests/`)→audit→**auto-rollback** on fail. Operator launches ultracode → PR → I review+merge. Then T3b UI; the BREATHE retry (prompt #1 "use the edit_file tool") is queued after.** Then **T3 — apply** (a human-approved `proposed` row →
snapshot → write the guarded out-of-sandbox `aios/` path → verify (run suite) → audit → **auto-rollback on
failure**; ENFORCE §6.3: no-self-approval guard + two-snapshot integrity check) → **T4** (core edit,
`aios/security/*` = RED, applying blocked). BREATHE track (Ollama `qwen2.5-coder:7b`) parallel. **OPS:**
local root `.coverage` stale+gitignored → `uncovered` low-value until full `pytest --cov` (or `rm` → dormant).

**▶ PRIOR 2026-06-08: PRE-T2 RUNWAY (c) — GOLDEN-REGRESSION HARNESS — MERGED to `master` (`7095c25`,
PR #8); suite 193 passed / 1 skipped on Windows; reviewed on evidence (golden regen = ZERO diff = faithful;
`pytest tests/golden --collect-only` = 0 fixture tests collected) — no patch.**
Implemented `.aios/state/ULTRACODE_TASK.md` (c) directly in Claude Code. LOCKS the analyzer's
deterministic T1 findings against a FROZEN committed fixture so any future drift (refactor / threshold
tweak / radon version bump) fails a test instead of silently shifting the marquee feature's output before
T2. **Tests + fixture + golden JSON ONLY — NO `aios/` change, NO new deps, no security/frontend.**
- **Committed fixture** `tests/golden/fixture/` exercises every T1 type once: `pkg/__init__.py` (none) ·
  `pkg/orphan.py` (→`missing_test`; also `import pkg.tidy` = the frozen T0 import edge) · `pkg/tidy.py`
  +test (none — proves no over-flagging) · `pkg/bloated.py`+test (TODO line 1 →`todo`; 18-line func
  →`smell`) · `pkg/tangled.py`+test (7 `if`s, radon CC 8 →`complexity`).
- **Explicit thresholds baked in BOTH fixture + golden:** `long_function_threshold=15`,
  `complexity_threshold=5` (keeps the fixture small + the golden reproducible). `uncovered` intentionally
  OUT of the golden (no `coverage_data_path` → join dormant; a committed synthetic `.coverage` could
  freeze it later).
- **Golden** `tests/golden/expected_findings.json` = SORTED array of `{target_path,finding_type,evidence,
  symbol}` (4 findings). **Test** `tests/test_golden_analysis.py`: `pytest.importorskip("radon")`; build
  agent over the fixture (path_root=fixture → machine-independent paths); `assert sorted(actual)==golden`
  with an added/removed set-diff message + the hint to regen; **regen via `AIOS_UPDATE_GOLDEN=1 …pytest
  tests/test_golden_analysis.py`**. Plus a T0 invariant (5 modules + the `pkg.tidy` edge) and a
  load-bearing drift self-test (`complexity_threshold=999` drops `complexity` → set differs from golden).
- **Collection guard:** `tests/golden/conftest.py` `collect_ignore_glob=["fixture/*"]` so the fixture's
  stub `test_*.py` files (needed for the `missing_test` convention) are NOT collected as real tests
  (verified: 0 fixture tests collected).
**Verified:** full suite `188 passed, 4 skipped, 2 failed` — the 2 = SAME pre-existing/environmental
`test_security.py` (identical with changes stashed). +3 golden tests; golden regen idempotent. **NEXT:**
(c) is MERGED — the pre-T2 runway is complete EXCEPT (d), a §VIII `CLAUDE.md` frozen-core doc that Claude Code PROPOSES (operator approves → I apply; NOT an ultracode job) — proposal APPLIED 2026-06-08 (operator-approved §VIII change): the frozen-core bullet is now in CLAUDE.md §XI. **PRE-T2 RUNWAY COMPLETE** (a · create_file · b · c · d all done) → next is **T2** (propose-diff): the agent generates a fix DIFF for an open finding (YELLOW + diff preview, status open→proposed), needs the no-self-approval guard + two-snapshot integrity check (§6.3) and introduces an LLM into self-analysis — design settled (operator went with my recommendations). **T2 ultracode SPEC WRITTEN & CURRENT** at `.aios/state/ULTRACODE_TASK.md` — propose-only/GREEN (reads source + writes the report's `proposed_diff`; NEVER writes source or applies), ALL finding types, injected completion LLM (local `qwen2.5-coder` default), `proposed_by`+`proposed_zone` as §6.3 groundwork (the no-self-approval guard + two-snapshot check are T3). Operator launches ultracode → PR → I review+merge. (Also applied this session: CLAUDE.md test baseline corrected 89→193.) Frozen core = `aios/security/{gateway,scope_lock,secret_scanner,audit_logger,injection_shield}.py`. Then runway **(d)** doc the frozen core in CLAUDE.md (§VIII: I
PROPOSE the diff, operator approves — NOT an ultracode job) → **T2** (propose-diff, YELLOW + no-self-
approval guard + two-snapshot check, §6.3) → T3 → T4. **OPS (unchanged):** the local root `.coverage` is
stale (1 file) + gitignored → live `self_analyze` emits low-value `uncovered` until a full `pytest --cov`
regenerates it (or `rm .coverage` → dormant). BREATHE track (Ollama `qwen2.5-coder:7b`) still parallel.

**▶ PRIOR 2026-06-08: PRE-T2 RUNWAY (b) — STATIC TOOLING (radon cyclomatic complexity + coverage join) —
MERGED to `master` (`f1b5e36`, PR #7); suite 190 passed / 1 skipped on Windows; reviewed on evidence +
independent live-tree smoke (radon active, 11 real CC findings, read-only) — no patch.**
Implemented `.aios/state/ULTRACODE_TASK.md` (b) directly in Claude Code. SHARPENS T1 before T2 turns
findings into proposals: replaced the AST branch-count `complexity` PROXY with **radon** real cyclomatic
complexity, and added a read-only **coverage join** → a new `uncovered` finding for testable modules the
suite never executed.
- **Fail-soft optional deps** (project's lazy-dep style): `try: from radon.complexity import cc_visit`,
  `try: import coverage` — both degrade if absent (radon→proxy fallback kept; coverage→dormant). Module
  imports + suite runs even without radon.
- **radon** in `_scan_source_findings`→ new `_complexity_findings(src,tree,rel_path)`: `cc_visit(src)` is
  read-only AST; iterate the FLAT block list, keep `letter in ('F','M')` (functions/methods; skip 'C'
  classes — methods appear flattened), emit `complexity` for `block.complexity > threshold`, **symbol =
  bare `block.name`** (fingerprint-stable: proxy→radon UPDATES existing open rows, no dup). radon raising
  on exotic source → per-file fallback to `_complexity_proxy_findings` (the old branch-count, kept).
- **coverage join** in `diagnose`: `__init__(coverage_data_path=None)`; `_measured_files()` reads an
  EXISTING `.coverage` (default `path_root/.coverage`) via `CoverageData(basename=…).read()` →
  realpath set; a testable module (defines func/class, not `__init__`) whose realpath ∉ measured →
  `Finding(rel_path,"uncovered","module has no executed lines in the coverage data")`. Dormant when no
  coverage/no file. Binary never-executed signal (partial-% deferred); `dead_code` deferred (needs vulture).
- `analyze()` stays PURE/read-only (radon parses, coverage only reads); **NO `tool_agent.py` change** (the
  summary counts finding types generically) · **NO frontend** · **NO `aios/security/`**.
**Deps:** added `radon==6.0.1` to `requirements.txt`. **FLAG (deviation-for-correctness):** the spec said
"only radon", but this requirements.txt is a fully-pinned FLAT list (all transitive deps pinned), so I
also pinned radon's transitive dep `mando==0.7.1` (radon's other deps colorama/six already pinned) — an
incomplete pin list breaks reproducible installs. Noted in the PR.
**Verified:** full suite `185 passed, 4 skipped, 2 failed` — the 2 = SAME pre-existing/environmental
`test_security.py` (identical with changes stashed). +5 self-analysis tests (radon real metric · proxy
fallback via monkeypatch `_radon_cc_visit=None` · coverage `uncovered` flags unmeasured / not measured ·
dormant w/o data · diagnose-with-coverage read-only). **Real-path smoke:** live `aios/` → 11 complexity
findings all "cyclomatic complexity N (> 12)" w/ bare symbols, no crash; coverage dormant (no root
`.coverage`). **NEXT (BUILD track):** (b) is MERGED. **OPS NOTE (verified at PR #7 review):** the local root `.coverage` is STALE (measures only `aios/api/main.py`) + gitignored, so live `self_analyze` emits ~24 low-value `uncovered` findings until a full `pytest --cov` regenerates it (or `rm .coverage` → the join goes dormant); the radon CC path is solid (11 real findings on live aios/). Then runway **(c)** golden-regression
harness for the analyzer (freeze findings over a fixture; catch drift; no new deps) → **(d)** doc the
frozen core in CLAUDE.md (§VIII: I PROPOSE the diff, operator approves) → **T2** (propose-diff, YELLOW +
no-self-approval guard + two-snapshot check, §6.3) → T3 → T4. BREATHE track (Ollama `qwen2.5-coder:7b`)
still available in parallel.

**▶ PRIOR 2026-06-08: `create_file` TOOL — author NEW files in the sandbox, behind the same human gate —
MERGED to `master` (`02f93cc`, PR #6); suite 185 passed / 1 skipped on Windows; reviewed on evidence +
an independent adversarial scope probe (aios/`../`/abs all REFUSED even with approval) — no patch.**
Implemented `.aios/state/ULTRACODE_NEXT_create_file.md` directly in Claude Code. THE GAP IT FILLS: the
agent could MODIFY files (`edit_file`, search/replace needs a non-empty `old_string`) but could not
AUTHOR a new one — blocking it from writing new tests/modules even in its sandbox. `create_file` adds
that behind the SAME gate as `edit_file` (NOT a new security path):
- **Scope-locked** to `config.SCOPE_ROOTS` via the same `is_path_in_scope(read_root/filepath)` check;
  a `../`/abs/symlink escape (`_resolve_within` → None) or any out-of-sandbox path (e.g. `aios/x.py`)
  is REFUSED, even with an approval supplied. **Refuses to overwrite** an existing file → error pointing
  to `edit_file` (create_file is for NEW paths only).
- **YELLOW + paused**: an unapproved create pauses with a `human_required` carrying an all-additions diff
  preview (`difflib.unified_diff([], content, fromfile="/dev/null", tofile=...)`) + a `{filepath,content}`
  creation payload; resumes only when re-sent with `approvedCreations` (keyed by filepath → apply EXACTLY
  the approved content, robust to model drift on replay — same lesson as `edit_file`).
- **Snapshot + audit FIRST, both fail-closed**, then write (mirrors `_edit_file`): pre-create snapshot
  ("before" = file absent, so rollback deletes it), `log_action("CREATE: …", YELLOW)`, then `mkdir(parents)`
  within scope + `write_text`. A snapshot OR audit failure → blocked, file NOT created.
**Files:** `tool_agent.py` (TOOL_SPECS `create_file` + docstring; `__init__` `approved_creations` map;
`_dispatch` route; `run()` approval branch carrying `creation`+`diff`; new `_create_file`) · `api/main.py`
(`approvedCreations` request field → `ToolAgent`; `human_required` handler `creation` branch → `input.creations`
+ diff) · `frontend/src/App.jsx` (`approvedCreations` state + `streamGenerate` 4th arg/body + approve/reject/
send wiring; approve button reads "Create file") · `MessageBubble.jsx` (🆕 TOOL_META + ✏️ edit_file) ·
`DiffView` reused for the all-additions preview. **NO `aios/security/` change.** **Verified:** full suite
`180 passed, 4 skipped, 2 failed` — the 2 are the SAME pre-existing/environmental `test_security.py` cases
(confirmed identical with changes stashed). +8 backend create tests (pause-with-preview · apply-approved+
snapshot despite drift · audit-applied · refuse-existing · out-of-scope blocked · `../` escape blocked ·
fail-closed on audit AND snapshot). Frontend **eslint clean + vitest 10/10** (+1 DiffView all-additions
test) **+ vite build** green. Smoke: `GenerateRequest(approvedCreations=…)` + `ToolAgent(approved_creations=…)`
wire cleanly; `create_file` in TOOL_SPECS. **NEXT (BUILD track): (b) static tooling — SPEC WRITTEN &
CURRENT** at `.aios/state/ULTRACODE_TASK.md` (operator OK'd deps 2026-06-08). radon real cyclomatic
complexity (replaces the branch-count proxy) + a read-only coverage join (new `uncovered` finding from an
existing `.coverage`); fail-soft, `analyze()` stays PURE, fingerprint-stable (complexity symbol = bare
func name), NO tool_agent/frontend/security change. **Only NEW dep = `radon`** (coverage 7.14.1 +
pytest-cov 7.1.0 already in requirements.txt). Operator launches ultracode on it → PR → I review+merge.
Then **(c)** golden-regression harness → **(d)** doc frozen core in CLAUDE.md (§VIII: I PROPOSE the diff)
→ **T2** (propose-diff, YELLOW + no-self-approval guard + two-snapshot check, §6.3) → T3 → T4. **BREATHE
track** (sandbox first breath on Ollama `qwen2.5-coder:7b`) still staged + available in parallel —
`create_file` now lets the agent author NEW files in its sandbox too (richer breath).

**▶ PRIOR 2026-06-07: PRE-T2 RUNWAY (a) — FINGERPRINT-RECONCILE FOR `self_analysis_report` — MERGED to
`master` (`17d96f5`, PR #5); suite 177 passed / 1 skipped on Windows; reviewed on evidence (no patch).**
Implemented `.aios/state/ULTRACODE_TASK.md` directly in Claude Code (operator asked me to build it, not
ultracode this time). THE NIT IT KILLS: PR#4's `write_report` did a plain INSERT per finding at
`status='open'`, so every `self_analyze` re-run piled up DUPLICATE open rows — T2 would then propose the
same fix N times. FIX: each `Finding` now carries a line-number-free `symbol` (func name / trimmed TODO
text / "" for one-per-module), and `finding_fingerprint = sha256(target_path\x1f finding_type\x1f symbol)`
gives a STABLE identity across runs (evidence/line numbers refresh; fingerprint doesn't).
`write_report` is now a SCOPE-CONFINED RECONCILE (→ `ReconcileResult{inserted,updated,closed,skipped,
open_total}`): decided rows (proposed/approved/applied/rejected/rolled_back) are SKIPPED (never
re-opened/duped); a matching open row is UPDATED (evidence refreshed); a new finding is INSERTED;
a vanished open finding is CLOSED (deleted — open rows are undecided + regenerable; decided rows are
NEVER deleted = the audit/decision lineage). Schema: `fingerprint TEXT` column added after `evidence`;
`db.py` gained an idempotent `_migrate` (ALTER ADD COLUMN on legacy DBs + DROP legacy open NULL-fp rows
+ a UNIQUE partial index `idx_sar_open_fp ON (fingerprint) WHERE status='open'` — created in `_migrate`,
not schema.sql, so it runs only after the column exists on fresh+migrated DBs). `_self_analyze` summary
now reports `{open_total} open ({inserted} new, {closed} resolved)` (kept the `Self-analysis of '{path}'`
+ `finding(s)` substrings a test pins). `analyze()` stays PURE/read-only; `aios/security/` untouched;
NO frontend change (per spec). **Verified:** full suite `172 passed, 4 skipped, 2 failed` — the 2 are
the SAME pre-existing/environmental `test_security.py` cases (confirmed identical with my changes
stashed). +6 reconcile tests (idempotent re-run · don't-reopen-decided · close-vanished · fingerprint-
stable-when-TODO-moves · scope-confined · legacy-DB migration) + the persistence test updated. **Real-
path smoke:** ran `self_analyze` over the live `aios/` TWICE → run1 inserted 45 / run2 inserted 0,
updated 45, 45 unique fingerprints = 45 rows (NO dup accumulation); `REAL_SOURCE_UNCHANGED: True`.
**NEXT (BUILD track): `create_file` tool is now CURRENT + UNBLOCKED** — spec at
`.aios/state/ULTRACODE_NEXT_create_file.md`; operator launches ultracode → PR → I review+merge. Then
**(b)** static tooling (radon cyclomatic + coverage.py join; heavy/new-deps → ultracode, spec issued
after this so it reflects the reconcile shape) → **(c)** golden-regression harness → **(d)** doc the
frozen core in CLAUDE.md (§VIII: I PROPOSE the diff, operator approves) → **T2** (propose-diff, YELLOW +
no-self-approval guard + two-snapshot check, §6.3) → T3 → T4. ((a)'s spec file `ULTRACODE_TASK.md` was
deleted post-merge — it lives in PR #5 + experiences.)

**▶ PRIOR 2026-06-07 (resumed). Operator gave the GO for the whole pre-T2 runway in my recommended
order: (a) report-row hygiene → (b) coverage/radon → (c) golden tests → (d) doc frozen core → T2 → T3
→ T4.** WORKING MODEL set this session: **ultracode (Claude-web) BUILDS the heavy items; Claude Code
(local) REVIEWS its PR on evidence + MERGES** — the proven #1–#4 loop. HONESTY (CLAUDE.md §0/§X): I
cannot launch ultracode or `/code-review ultra` myself (operator's browser/billed action); my half is
the airtight spec + the evidence review + the merge. (NOTE: for (a) the operator routed the build to me
directly — done above.)
**TWO PARALLEL TRACKS (decided this session):**
- **BUILD track (ultracode builds → I review+merge):** **(a) fingerprint-reconcile = MERGED (PR #5,
  `17d96f5`, 177/1).** **CURRENT = `create_file` tool** (`.aios/state/ULTRACODE_NEXT_create_file.md`) —
  operator launches ultracode → PR → I `gh pr checkout`, run the Windows baseline, review on evidence,
  squash-merge. Then (b) coverage/radon → (c) golden tests → (d) doc frozen core (§VIII) → T2→T4.
- **BREATHE track (the AI-OS dogfoods itself in its sandbox, on Ollama):** seed pair staged
  (untracked) — `training_ground/greeter.py` (planted bug: `greet()` drops the name) +
  `training_ground/test_greeter.py` (fails until fixed). Operator runs backend+frontend, picks
  `qwen2.5-coder:7b`, and drives the full loop: read → (run pytest, fail) → reflect 🧠 → propose
  `edit_file` diff → APPROVE (YELLOW) → snapshot+write → verify (pass) → lesson promoted. This is the
  first real breath; it stays OFF the build track's critical path. KEY FACT: the agent can ONLY write
  inside `training_ground/` (SCOPE_ROOTS); editing its own `aios/` source is auto-RED — that is T2+,
  the guarded evolution step, NOT a shortcut.

`git status` noise (`training_ground/data.json` + the PDF + 4 parked CSS + the 2 new seed files) is
expected, not drift. HONESTY (§0): I cannot launch ultracode or the Ollama run — those are the
operator's physical actions; I spec, stage, watch pasted output, and review+merge.

**▶ CURRENT (2026-06-07): SELF-ANALYSIS MODULE — READ-ONLY FOUNDATION (T0 + T1) — DONE, REVIEWED
ON EVIDENCE, & MERGED to `master` (PR #4 → squash `4cb01b6`). Full suite 171 passed / 1 skipped
on Windows; brain pushed.**
The first, zero-risk slice of the AUDIT's marquee feature (Assessment §6). STRICTLY READ-ONLY:
never edits source, never executes, loads NO model — pure stdlib (`ast`/`pathlib`/`hashlib`/`re`).
T2 (propose-diff) / T3 (apply) / T4 (core edit) are LATER increments — deliberately NOT built.
**(1) `aios/agents/self_analysis_agent.py` — `SelfAnalysisAgent`.** Default scope = the `aios/`
package under `config.PROJECT_ROOT`; `scope_root`/`tests_root`/`path_root`/`db_path` all injectable
(tests point it at a fixture tree). **T0 (index):** per-module `ModuleFacts` via `ast` — rel path,
LOC, function names, class names, imports — + a simple intra-package import/dependency map.
**T1 (diagnose):** deterministic `Finding(target_path, finding_type, evidence)` — `missing_test`
(a testable module, i.e. defines a func/class & not `__init__`, with no `tests/test_<stem>.py`),
`smell` (>40 LOC defining nothing, or an over-long function), `todo` (TODO/FIXME/XXX/HACK + line),
`complexity` (AST branch-count proxy over a threshold). Deterministic facts ONLY — no LLM
commentary this increment (`llm_commentary`/`proposed_zone`/`proposed_diff` left NULL; trust
evidence, not the model). `analyze()` is pure/read-only; `write_report()`/`read_findings()`
persist/query (ensure schema via idempotent `init_memory_db`). TODOs left for the later
coverage.py join + radon metric + dead_code.
**(2) `self_analysis_report` table** added to `aios/memory/schema.sql` via the existing idempotent
`IF NOT EXISTS` pattern (same MEMORY_DB), schema per §6.4 (id, timestamp, target_path,
finding_type, evidence, llm_commentary, proposed_zone, proposed_diff, status DEFAULT 'open' w/
CHECK, applied_audit_id) + the two indexes (status, target_path).
**(3) Wired READ-ONLY as a `self_analyze` tool** in `tool_agent.py` (mirrors verify/plan): TOOL_SPECS
entry (optional `path`, default `aios`); `_dispatch` → `_self_analyze`, which confines `path` with
the SAME `_resolve_within(self.read_root, …)` resolver as `read_file` (refuses `../`/abs/symlink
escape), runs the agent, writes the report, returns a summary (counts by finding_type + top 8).
status `ok`, `failed=False` — read-only, never reflected. Frontend: one additive `MessageBubble.jsx`
TOOL_META entry (🔬 "Self-analysis").
**Verified:** new `tests/test_self_analysis.py` (7) all pass — T0 map (funcs/classes/LOC/imports +
intra-edge), T1 todo(+line)/smell/missing_test, over-long-function smell, write→read rows (open,
T2 cols NULL), **source-hash-unchanged before/after (never writes source)**, tool returns a
summary, path-escape refused. Full suite `166 passed, 4 skipped, 2 failed` — the 2 fails are the
SAME PRE-EXISTING + ENVIRONMENTAL `test_security.py` cases (Windows `C:\…` path GREEN on Linux +
`/tmp/pytest-…` entropy false-positive), confirmed IDENTICAL with my changes stashed. Frontend
**eslint clean + vitest 9/9 + vite build** all green. **Real-path smoke:** ran the analyzer over
the live `aios/` (31 modules, 41 findings {missing_test 20, complexity 11, smell 5, todo 5}, 65
intra-package import edges, clean DB round-trip). Frozen security core untouched.
**REVIEW (2026-06-07, Windows, evidence):** checked out PR #4 → full suite **171 passed / 1
skipped** (164 baseline + 7); frontend **eslint + vitest 9/9 + build** green; **independently
reproduced** the real-tree smoke (31 modules, 41 findings {missing_test 20, complexity 11, smell 5,
todo 5}, 65 import edges) AND re-proved READ-ONLY by SHA-256-hashing the live `aios/` tree
before/after a full `analyze()`+`write_report()` (`REAL_SOURCE_UNCHANGED: True`); confirmed
`_resolve_within` is the SAME fail-closed resolver `read_file` uses (escape → `tool_blocked`),
`get_connection` commits, frozen `aios/security/` untouched. Correct as-submitted — no patch needed
(like PR #3). The one brain-file (RESUME.md) conflict was resolved by merging `origin/master` INTO
the branch (took ours), pushing, then squash-merging (`gh pr merge 4 --squash --delete-branch`).
**NEXT ACTION (decide as CEO + Architect — propose ONE, then wait for the go):** the runway before
T2 — **(a) report-row hygiene** (the only nit that bites T2: live `self_analyze` always INSERTs
every finding as `open`, so re-runs accumulate duplicate rows → add a scan/run grouping or de-dup
BEFORE T2 turns findings into proposals); **(b) static tooling** (coverage.py + radon — turn the
TODO proxies into real metrics + refine the coarse `missing_test` heuristic); **(c) golden-regression
harness**; **(d) document the frozen core in CLAUDE.md**. THEN **T2 (propose-diff, YELLOW + diff
preview)** → **T3 (apply: snapshot → verify → audit → auto-rollback)** → **T4 (core edit, RED,
frozen)**. T2+ also needs the no-self-approval guard in the approval endpoint + the two-snapshot
integrity check (§6.3).

**(prior 2026-06-07): TIER-2 HARDENING — ROLLBACK GIT-DB OUT-OF-TREE (#3) + TEST DATA_DIR
ISOLATION (#4) — DONE & GREEN — MERGED (PR #3).** Cleared the two AUDIT.md Tier-2 structural-debt
items in ONE focused PR, kept as two separable changes each with its own tests.
**FIX #3 (rollback repo inside the tracked tree):** the engine snapshotted a git repo INSIDE
`config.SCOPE_ROOTS[0]` (`training_ground`), which the MAIN repo tracks → embedded-repo wrinkle
+ `training_ground/.gitkeep` showed untracked. Added `config.ROLLBACK_DIR` (default
`DATA_DIR/"rollback"`, gitignored; `AIOS_ROLLBACK_DIR` overridable). `RollbackEngine` now keeps
the sandbox as the git WORK-TREE but puts its git DATABASE under `ROLLBACK_DIR` via
`Repo.init(work_tree, separate_git_dir=...)`, leaving only a tiny `gitdir:` POINTER file in
`training_ground/`. Re-opening via the work-tree transparently follows that pointer (history
preserved). An injected `repo_dir` (tests, already a tmp dir) keeps its DB in-tree — original
behavior intact; project-root refusal guard untouched. Also gitignored `training_ground/.git`
+ `training_ground/.gitkeep` (local scratch, like `data/`). **Verified in the real production
path:** `training_ground/.git` is a 43-byte pointer, the real DB (HEAD/objects) is under
`data/rollback/`, and `git status` shows NO `training_ground/.git*` or `.gitkeep` (all gitignored,
confirmed via `git check-ignore`). +3 tests in `tests/test_rollback.py` (DB out-of-tree + e2e
snapshot/rollback through external DB · reopen-via-pointer preserves history · injected repo_dir
stays in-tree).
**FIX #4 (tests shared the live DATA_DIR):** added `tests/conftest.py` that sets
`os.environ["AIOS_DATA_DIR"]` to a fresh `tempfile.mkdtemp` at MODULE level — before `aios.config`
is first imported — so config derives DATA_DIR / MEMORY_DB_PATH / AUDIT_DB_PATH / FAISS_INDEX_PATH
/ ROLLBACK_DIR under the temp dir for the whole session; the real `data/` is never read/written
(atexit cleanup). An isolated temp index is empty, so `hybrid_search` short-circuits to `[]`
WITHOUT loading the embedder — so I REMOVED the now-unnecessary `client`-fixture `hybrid_search`
stub in `tests/test_api.py` (no model/network/shell side-effect added to any test path; the
contract is pinned by a test). +3 tests in new `tests/test_data_isolation.py` (DATA_DIR is the
temp dir, not project `data/` · all derived paths live under it · `hybrid_search` returns `[]`
on the empty index with `EmbeddingModel.instance` made to explode if loaded).
**Verified this env:** full suite `159 passed, 4 skipped, 2 failed` — the 2 fails are the SAME
PRE-EXISTING + ENVIRONMENTAL `test_security.py` cases (Windows `C:\…` path classified GREEN on
Linux + a random `/tmp/pytest-…` dir tripping the entropy scanner); confirmed they fail
IDENTICALLY with my changes stashed (they are not mine). Frozen security core + frontend
untouched. **NEXT:** operator reviews/merges the draft PR, then (5) **Self-Analysis module** —
now fully unblocked: plan-before-act + verify-after + a clean rollback engine all live, so
apply→verify→auto-rollback has every piece; its tests can rely on real DATA_DIR isolation.

**(prior 2026-06-07): PLANNER + CONFIDENCE GATE WIRED INTO THE LIVE LOOP — DONE & GREEN
(branch `claude/sharp-heisenberg-q2C1L`, draft PR #2 → operator review → merge → `git pull`).**
AUDIT Tier-1 #2, mirroring the merged `verify` pattern (PR #1). Added a `plan` tool to
`aios/agents/tool_agent.py`: new TOOL_SPECS entry (one `goal` param) routed in `_dispatch`
to `_plan`, backed by `Planner(planner_llm)` built ONCE in `__init__` (reuses `planner.py`,
not rewritten). **CRITICAL client split honored:** the Planner needs a COMPLETION client
(`.complete()`), NOT the loop's chat client `self.llm` (may be cloud Bedrock, no
`.complete()`) — so `ToolAgent.__init__` takes an injected `planner_llm: Optional[LLMClient]`,
and `main.py /api/generate` passes it via `Depends(get_llm_client)` (the local completion
model, same dep `/api/v1/plan` + reflection use). `_plan` is ADVISORY + fail-soft: no planner
→ `[plan unavailable]`; `PlannerError` → `[plan error] …`; success → ordered steps w/
confidences + an explicit "N step(s) need human review (confidence < 0.72): …" section when
`requires_human`. ALWAYS status `ok`, `failed=False` — planning is never a security block and
never reflected on; real actions still pass the gate + approval. Did NOT auto-plan per turn,
did NOT pause-on-`requires_human` (out of scope). Frontend: one additive `plan` TOOL_META
entry (📋 "Plan"). +4 tests in `tests/test_tool_agent.py` (lists steps · flags <0.72 step ·
PlannerError surfaced cleanly, no reflect · graceful unavailable + loop still `done`).
**Verified this env:** backend `152 passed, 4 skipped, 2 failed` — the 2 fails are the SAME
PRE-EXISTING + ENVIRONMENTAL `test_security.py` cases (Windows `C:\…` path + a random
`/tmp/pytest-…` dir tripping the entropy scanner; identical with my changes stashed; Windows
baseline 153/1). Frontend **vitest 9/9 + build + eslint all green** (deps installed this run).
**NEXT:** operator reviews/merges PR #2, then (3) rollback nested-`.git` + DATA_DIR isolation,
(4) static tooling + golden tests + pull `qwen2.5-coder:7b`, (5) **Self-Analysis module** (now
fully unblocked: plan-before-act + verify-after both live → apply→verify→auto-rollback has its
pieces).

**(prior 2026-06-07): VERIFIER WIRED INTO THE LIVE LOOP — DONE & GREEN (branch
`claude/sharp-heisenberg-q2C1L`, draft PR → operator review → merge → `git pull`).**
Closed the AUDIT.md KEY GAP (Verifier built but "wired to nothing"). Added a `verify`
tool to `aios/agents/tool_agent.py`: a new TOOL_SPECS entry (one `command` param) routed
in `_dispatch` to a `Verifier(self.executor, on_failure=self.on_failure)` built ONCE in
`__init__` (reuses `verifier.py`, not rewritten). `_verify` calls
`.verify(command, session_id=...)` and maps `VerifierResult` → the loop's
`(output, status, failed)` shape: a security BLOCK → `tool_blocked` (RED/out-of-scope
verify refused by the gateway, never run — not bypassed); a pass/fail → `tool_result`
with a `[VERIFY PASS|FAIL] N passed, M failed (exit C)` line + summary the model/UI see.
Fail-closed kept. **No double-reflect:** the Verifier fires `on_failure` itself; `run()`
only reflects for `execute_terminal`, so the dispatch path adds none. Frontend: one
additive `verify` entry in `MessageBubble.jsx` `TOOL_META` (✅ "Verify"). +3 tests in
`tests/test_tool_agent.py` (pass→no reflect · fail→reflects once · RED→blocked, runner
never called). **Suite on Linux: 148 passed, 2 failed, 4 skipped — the 2 fails are
PRE-EXISTING + ENVIRONMENTAL** (test_security.py: a `C:\Windows\...` path + a random
`/tmp/pytest-…` dir name tripping the entropy scanner; both fail identically with my
changes stashed — Windows baseline was 150/1). All tool_agent + verifier tests pass.
**NEXT:** operator reviews/merges the draft PR, then **(2) wire Planner+confidence** into
the live loop (next build step), then (3) rollback nested-`.git` + DATA_DIR isolation,
(4) static tooling + golden tests, (5) Self-Analysis module (now unblocked: apply→verify
→auto-rollback has its verify).
NOTE (this env): no `.venv` checked in; tests run via a throwaway venv with the ML
training stack (torch/transformers/sentence-transformers) omitted — they're lazy-loaded
and the suite stubs the embedder, so faiss+numpy suffice. Windows run cmd unchanged.

**(prior 2026-06-06): edit_file path bug FIXED + committed `68653dc` (master).** The live e2e
"file is empty" error was a path-doubling bug — `edit_file` resolved sandbox-relative while reads
resolve project-relative, so `training_ground/data.json` → `training_ground/training_ground/data.json`
(nonexistent). Fixed `_edit_file` to resolve under `read_root` before the scope check (frozen
`scope_lock` core untouched) + a regression test + aligned test fixtures. **Suite: 150 passed, 1
skipped.** Now standing up a **private GitHub remote** so the operator can use Claude-web "ultracode"
(local box is RAM-bound). `gh` v2.93 installed + authed (**swap821**). **DONE — private remote LIVE:** `origin` =
https://github.com/swap821/ai-editor · `master` pushed (fix `68653dc` on origin/master) · no secrets
tracked. **NEXT (operator, browser): (1)** connect the repo to Claude-web (authorize the Claude GitHub
app) to enable ultracode/PRs; **(2)** add the ABSK key + region as cloud secrets
(`AWS_BEARER_TOKEN_BEDROCK`, `AIOS_BEDROCK_REGION`), never committed; **(3)** run the live e2e of the
fix (Bedrock): change hello→hi in `training_ground/data.json` → approval bar shows the diff → Apply →
file updated + pre-edit snapshot.
**✅ E2E VERIFIED (2026-06-07, live Bedrock):** diff shown → Apply → `training_ground/data.json` =
`{ "greeting": "hi" }`; pre-edit snapshot `dce2427` in the nested `training_ground/.git`. The full
chain (model → edit_file → diff → human approval → snapshot → write) is proven in the real app — the
edit_file path bug is fully closed. Steps 1–2 (connect repo to Claude-web + cloud secrets) remain
optional for *cloud* runs. **NEXT (2026-06-07): operator pivoted to BACKEND.** Full backend check-up done →
`.aios/state/AUDIT.md` (core ≈90% test-backed, 150/1; KEY GAP = Planner/Verifier/Confidence built but
NOT wired into the live `/api/generate` loop). Build order: **(1) wire the Verifier into the live loop
via ultracode** (prompt drafted; PR → I review locally → merge → `git pull`); (2) wire
Planner+confidence; (3) fix rollback nested-`.git` + test/DATA_DIR isolation; (4) static tooling +
golden tests + pull `qwen2.5-coder:7b` (16 GB RAM now); (5) **Self-Analysis module** (marquee feature,
v6 assessment §6). UI deferred. Brain syncs to origin (swap821/ai-editor) via the cloud workflow.

--- (prior next-action history below) ---
**PHASE 1+2 DONE; SLICE 1 (1a+1b) DONE & GREEN (2026-06-03).** Full suite **124 passed,
1 skipped**. `PLAN.md` targets **100% / no left-outs** (fundamentals-first; deferrals are
later phases, not dropped).
- **Slice 1a — security-scope hardening (FROZEN CORE): DONE & committed (`e7bba3c`).**
  Fixed 3 live scope bypasses an xhigh review found in the prior `command_stays_in_scope`
  rewrite (`~/…` home, shell-metachar-glued abs paths, bare `..` — all had classified
  GREEN). `_SHELL_OPS` pre-split + `~` refusal + `..` guard; 5 regression tests; legit
  `.venv\Scripts\python.exe`/`&&` cases still YELLOW.
- **Slice 1b — API contract tests: DONE & GREEN (uncommitted).** 8 HTTP tests in
  `tests/test_api.py` for `/plan,/execute,/approval/req,/rollback`; the 4 route handlers
  are now fully covered. The `/approval/req` test pins the D1 hard-block at the HTTP layer.
- **D1 (RED policy): DECIDED — keep hard-block** (RED always refused even after approval;
  stricter than the blueprint, by choice). Recorded in `PLAN.md` + memory.
- Operator memories saved (independent dev; 100% goal; CEO role) + `CEO_LOG.md` (Advice #1).
  Commits: `e39a3f8` v6 · `e7bba3c` scope fix · `2b657dd` blueprint cleanup · `ba5d838` planning.
- **Slice 2 — file-edit tool (patch-style `edit_file`), backend: DONE & GREEN.** Per
  operator, built as search/replace (unique old_string → unified-diff preview → YELLOW
  pause → pre-write snapshot + write + audit on approval), scope-locked to sandbox roots.
  5 tests in `test_tool_agent.py`. Live path stays SAFE: `edit_file` always pauses until
  Slice 4 wires `approvedEdits` + the snapshot/diff UI. Full suite **129 passed, 1 skipped**.
- **Slice 3 — frontend test harness: DONE & GREEN.** Installed vitest + RTL + jsdom
  (operator-approved). Extracted the SSE frame parser to `src/lib/sse.js` (wired into
  `App.jsx` streamGenerate, behavior-preserving) + vitest config/setup + `npm test` script.
  Tests: `sse.test.js` (4) + `MessageBubble.test.jsx` (3) = **7 passing**; `npm run build` clean.
- **Slice 5 — Verifier stage (Blueprint stage 8): DONE & GREEN.** New `aios/core/verifier.py`
  runs a test command through the gated Executor, judges pass/fail by exit code + parsed
  pytest/jest counts, returns a bounded confidence delta, and feeds failures to a reflection
  hook (fail-closed on blocked/timeout). 5 tests. Full suite **134 passed, 1 skipped**.
- **Slice 7 — L3 entity facts + contradiction detection (Blueprint 5.3): DONE & GREEN.**
  New `semantic_facts` table + `aios/memory/facts.py` (`SemanticFacts`): `(subject,predicate,object)`
  triples; `add_fact` detects a same-subject+predicate / different-object **contradiction** and
  refuses to silently commit it (returns the conflict to route to reflection/human); `reconcile`
  supersedes + commits the chosen object; exact duplicates idempotent. 4 tests. Full suite **138 passed, 1 skipped**.
  Frontend-polish-worker idea now recorded **permanently in memory** (`frontend-polish-worker-idea`) + PLAN.md.
- **Slice 4 — diff-preview approval (CODE HALF): DONE & GREEN.** 4a (backend, committed `e5bfbc7`):
  `approvedEdits` + a lazy pre-write snapshot wired through `/api/generate`; the edit `human_required`
  SSE carries the diff + edit triple. 4b (frontend): a `DiffView` component renders the unified diff
  in the (unchanged, working) approval bar; `approvedEdits` state + resume wired
  (`handleApproveAction`/`handleRejectAction`/`streamGenerate`). Frontend **9 tests** (DiffView ×2);
  `npm run build` clean; backend 140.
- **Slice 4c — hardening pass (DONE & GREEN):** fixed all 8 findings from the max-effort self
  /code-review of this session's code. `edit_file` is now **fail-closed on snapshot AND audit** (a
  failure of either blocks the edit), **audits before writing**, and applies the *approved* edit by
  **filepath** (robust to a local model regenerating drifted args on resume); verifier **trusts the
  exit code** + **skips reflection on security blocks**; `facts.reconcile` rejects empty; App.jsx
  approve message fixed. +6 tests. Full suite **146 passed, 1 skipped**; frontend 9; build clean.
- **Slice 6 — prompt-injection vector blocklist (FROZEN CORE, operator-approved): DONE & GREEN.**
  `aios/security/injection_shield.py` (`VectorInjectionShield`) embeds a curated injection set and
  flags inputs with cosine ≥ threshold; `gateway.classify` consults an installed shield after the
  regex layer. Deterministic · fail-safe (embedder error → regex-only) · opt-in (`AIOS_INJECTION_VECTOR_SHIELD`,
  default off; API installs it at startup when set). 3 tests; all prior security tests pass regex-only.
  Full suite **149 passed, 1 skipped**.
- **Bedrock re-enabled + LIVE on cloud (2026-06-04): WORKING.** Operator ran the agent on AWS Bedrock
  (RAM-free): `query_knowledge` + `read_directory` + `read_file` all executed via the gated tools, the
  cloud model reliably emitted tool calls, and it **correctly declined to edit an EMPTY `data.json`**
  (`edit_file` is search/replace — nothing to match; the safe behavior we built). So the **cloud pipeline
  + agentic loop + tool-calling + reasoning are CONFIRMED working.** Verified this boto3 (botocore 1.43.20)
  supports the `ABSK` bearer token via dynamic `AWS_BEARER_TOKEN_BEDROCK`+`httpBearerAuth`; fixed the
  dropdown's fictional model ids → real Nova/Claude/Llama/Mistral ids; documented env in `.env.example`.
**Next action — OPERATOR (finish the e2e, one step left):** seed a file with content
(`Set-Content training_ground\data.json '{ "greeting": "hello" }'`), then ask the agent to change
"hello"→"hi" via `edit_file` → confirm the **approval bar shows the diff** → Apply → file written +
`[SNAPSHOT] pre-edit` in `git -C training_ground log`. That's the only unexercised piece. Then **Slice 8**
(polish/freeze). NOTE: no "create file" tool yet (`edit_file` is patch-only) — acceptable for MVP; could
add a `create_file` tool later. Later phases: voice, KG, Docker, chaos/perf, frontend-polish worker.
**Parked:** 4 untracked premium CSS files (intentional, for a later polish phase).

--- (prior Phase-4h candidates, retained for context) ---
**Phase 4h is DONE and committed.** Pick the next build step. Candidates, in rough
priority (propose one, then STOP for the operator's go before writing code):
1. **Live e2e demo pass (RAM-gated).** Load `llama3.2:3b`, run backend + frontend,
   and walk the full happy path: chat → YELLOW command → approval card → resume →
   command runs → reflection. This is the highest-value next step (proves 4h end-to-end)
   but needs ~4 GB free RAM (close other apps). Set `AIOS_INDEX_CHAT=false` /
   `AIOS_REFLECT_ON_FAILURE=false` on a tight run to avoid extra model loads.
2. ~~Reject-on-resume polish~~ **DONE** — `handleRejectAction` now clears the
   approval whitelist + pending action and posts "Rejected — the command was not run."
3. **Offline voice (Whisper + Piper)** — fully local STT/TTS; bigger scope.
4. **Docker + Prometheus/Grafana** — packaging/observability; bigger scope.

The next *substantive* step is the live e2e demo (RAM-gated, operator-driven) — see
the runbook; free ~3 GB first (only 1.31 GB free at last checkpoint).

Note: approval whitelist is **per-request** (frontend resets `approvedCommands` on each
new user message; grows it only across an approve→resume chain). That's the intended
security boundary — re-check it if you change the resume flow.

Deferred (unchanged): offline voice; Docker + Prometheus/Grafana.

### Frontend stabilization (after a parallel rewrite broke it)
A concurrent "premium 2026" rewrite landed uncommitted in the tree (rewritten
`MessageBubble.jsx`/`LivePreview.jsx` with **incompatible props** — `{message,isUser}`
vs the `{msg}` the app passes — plus new `styles/{App,design-system,nexgen-3d,nexgen-layout}.css`
imported into App.jsx/index.css). It broke the chat render. Per operator choice we
**stabilized**: restored the working components + clean `index.css` baseline, stripped
the foreign imports, and **parked the 4 new CSS files untracked+unimported** (preserved,
not deleted) for the upcoming incremental polish. App builds clean; pinned approval bar kept.
**Next (polish phase):** layer premium polish onto the WORKING components one increment at a
time (verify build each step); optionally mine the parked CSS for ideas. Don't re-import it wholesale.

### Cloud inference (AWS Bedrock) — NEW, opt-in
Local Ollama CUDA-OOMs on the 4GB RTX 3050, so a **Bedrock cloud provider** was
added (`aios/core/bedrock.py`, Converse API + tool-use; routed in `/api/generate`
via `_select_chat_client`). Local-first stays the default; Bedrock is **off**
unless a region is set. Auth uses the operator's new **Bedrock API key** (`ABSK…`,
a bearer token — NOT an IAM `AKIA…` key) via `AWS_BEARER_TOKEN_BEDROCK`. The model
defaults to `amazon.nova-lite-v1:0`, so only **region + key** are needed:
```
$env:AIOS_BEDROCK_REGION      = "us-east-1"   # the operator's region
$env:AWS_BEARER_TOKEN_BEDROCK = "ABSK..."     # the Bedrock API key (env only)
# optional: $env:AIOS_BEDROCK_MODEL = "<other model/inference-profile id>"
```
Then in the UI pick a **Cloud (Bedrock)** model → routes to Bedrock on THAT model
(the selected id is passed through to Converse). Secrets live only in env.

**Model picker DONE:** `BedrockClient.list_models()` (control-plane
ListFoundationModels, TEXT+ON_DEMAND) → `/api/v1/models/bedrock`; the frontend
shows a real "Cloud (Bedrock)" group (curated fallback if discovery is blocked).
107 tests pass. NOTE: the test suite now stubs `aios.api.main.hybrid_search` in
the `client` fixture — live app usage had populated the on-disk FAISS index, so
generate tests were loading the real embedder and **segfaulting torch**; the stub
isolates tests from live `data/` (no model side-effects in tests).

## Open approvals / blockers
- Live happy-path is gated by host RAM (7.5 GB). Close other apps so `llama3.2:3b` fits (~4 GB free). `AIOS_INDEX_CHAT` and `AIOS_REFLECT_ON_FAILURE` each add an extra model load — set them `false` on tight runs.

## Active files  (Self-Analysis T2 propose-diff — on branch `claude/sharp-heisenberg-q2C1L`:)
- `aios/agents/self_analysis_agent.py` (`__init__ llm/frozen_subdirs` · `_classify_target` RED/YELLOW · `propose_fix` scrubbed diff via injected `.complete()`, fail-soft · `propose_open` open→proposed, report-only · `PROPOSER_ID`) · `aios/agents/tool_agent.py` (`self_analysis_llm` inject · `propose_fixes` TOOL_SPECS/docstring/_dispatch/`_propose_fixes`) · `aios/api/main.py` (`self_analysis_llm=planner_llm` into ToolAgent) · `aios/memory/schema.sql` (+`proposed_by`) · `aios/memory/db.py` (`_migrate` +`proposed_by` ALTER) · `tests/test_self_analysis.py` (+6 T2 tests). NO `aios/security/` / frontend change.
- (all merged:) verify (PR #1) · planner/plan (PR #2) · Tier-2 rollback-DB + DATA_DIR isolation (PR #3) · Self-Analysis T0/T1 (PR #4) · fingerprint-reconcile (PR #5) · create_file (PR #6) · radon+coverage static tooling (PR #7) · golden harness (PR #8).

## Notes not yet promoted to memory
- Run backend: `.venv\Scripts\python -m uvicorn aios.api.main:app --port 8000`. Run frontend: `cd frontend; npm run dev` (:5173). Tests: `.venv\Scripts\python -m pytest -q`.
- The repo uses per-phase commits on `master` (not `main`). Keep that cadence.

---
_Last updated: 2026-06-08 by Claude Code (T3a apply-engine spec written + CURRENT; chose (A) → T3a then T3b UI; BREATHE retry queued)_

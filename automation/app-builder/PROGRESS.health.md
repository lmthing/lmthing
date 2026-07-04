> ⚠️ **OUTSTANDING — operator directive (2026-07-04):** this app's round-1 project space was
> created with **only `agents/`**, which violates the space format. On the **next (expansion)
> round** you MUST remediate it to the **FULL space format**: add a `charter.md` per agent
> (alongside `instruct.md`), plus `tasklists/`, `functions/`, `components/`, and especially
> **extensive `knowledge/`** (each field = `index.md` overview + ≥2 `<aspect>.md` deep-dives).
> See `automation/app-builder/prompt.tmpl.md` → Phase 3 "Project-scoped spaces MUST follow the
> FULL space format" and the round policy's "SPACE-FORMAT REMEDIATION" item. This is required
> work, not optional.

# PROGRESS — `health` project-application

Running log across 5-hour autonomous runs. Single source of truth for status.

## Environment / ground truth (verified this run, 2026-07-04)
- Engine (`sdk/org/libs/{core,cli}`) is built **through Phase 8** (db, capability globals,
  api runtime, typed-contract build, pages build, hooks runtime, chat, Studio admin). Phase 9
  (`system-appbuilder`) is NOT built — so the health app is **hand-authored** under
  `store/projects/health/` (no appbuilder delegation needed). Same model blog + kitchen used.
- Output location (operator override): **`store/projects/health/`** in the monorepo. `types/` +
  `.data/` + `node_modules/` are generated/runtime → git-ignored.
- Reference implementations = `store/projects/blog/` + `store/projects/kitchen/` (round-1 shipped,
  live-verified). Health mirrors their file shapes exactly.
- `sdk/org/.env` has AZURE keys + `LM_MODEL_S` (= `azure:DeepSeek-V4-Flash`) — live model ready.
- CLI dist is built (`sdk/org/libs/cli/dist/cli/bin.js`).

### Key runtime contracts (from engine source + blog/kitchen round-1 logs)
- `database/<table>.json` → `validateSchemaSet` (fail-loud: required descriptions on
  table/column/relation, exactly-one PK, FKs/relations resolve). Column types
  `string|number|boolean|date|json`; flags `primaryKey/required/unique/default/generated(uuid|now)`;
  `references {table,column?,onDelete cascade|setNull|restrict}`;
  `relations {name:{hasMany|belongsTo, via, description}}`.
- **Row-interface names = deterministic singularizer** (`libs/cli/src/app/build/schema.ts`
  `tableInterfaceName`/`singularize`): split on `_`/`-`, singularize LAST word, PascalCase.
  Rule: `…{cons}ies`→`…y`; `…{s,x,z,ch,sh}es`→strip `es`; bare trailing `s` stripped only after a
  "normal" consonant (NOT after s/u/i). For health:
  - `metrics→Metric`, `lab_results→LabResult`, `symptoms→Symptom`, `research→Research` (unchanged —
    ends `ch` not `ches`), `sources→Source`, **`settings→Setting`** (trailing `gs`→`g`; NOT the
    spec-prose `Settings`).
  - **Spec was corrected**: all `Settings` type references → `Setting`; added a "Row-type note".
- `db.query` `where` is **equality-only** (`Record<string,unknown>`) + `include/orderBy/limit/offset`.
  No LIKE/ranges → agents/handlers query-all + filter in JS. `include:['rel']` = single-hop join;
  a 2nd hop is hydrated manually by id.
- api handler: ESM exporting `name`/`description`/`Input`/`Output` + default
  `async (input, ctx) => Output`; `ctx = { db: AsyncDbApi, spawn, apiCall }`; `import { HttpError }
  from '@app/runtime'`. Method = filename, route = dir, `[id]` merges into Input. **AsyncDbApi is
  Promise-returning** in handlers (await every db call); the AGENT surface is synchronous (no await).
  Handlers inline their own `Db`/`Ctx` types + row interfaces (they can't import `@app/types`).
- hooks: default-export object. cron `{type:'cron', every|daily, trigger, budget}`; database
  `{type:'database', on:{table,event}, trigger|handler, budget}`. Hook handler ctx = `{row, db, delegate}`.
- pages: default-export React `({ params }) => JSX`; data via `@app/runtime` `useApi`/
  `useApiMutation`/`apiCall`; `<Chat agent="space/agent" />`; router `Link`/`navigate`/`useParams`.
  Import row types from `@app/types`. Design tokens only (`@lmthing/css`) — no raw colors.
  Flag colors: `success` (normal) / `warning` (low) / `destructive` (high); charts use `primary`/`accent`.
- project-scoped spaces at `<projectRoot>/spaces/<space>/agents/<agent>/{instruct,charter}.md`. Agent
  frontmatter allow-list `{title,knowledge,functions,components,actions,defaultAction,canDelegateTo,
  dependencies,capabilities}`. `capabilities:` = list of bare id or `id:{config}`; `db:read/write/schema
  {tables?}`, `api:call {allow}` (required), `pages/api/hooks:write`. A named delegate action needs an
  `actions:` entry (empty tasklist = model-driven).
- **Engine gotchas already fixed by blog round (keep applying, do NOT reintroduce):** dynamic
  `[param]` api routes need the glob-escape in `build/schema.ts` (shipped `escapeGlobPath`);
  `functions:` in agent instruct validates against SPACE functions only — do NOT list system
  `webSearch/webFetch/fetch` there (they're universal globals; OMIT `functions:` to keep them);
  `where` is equality-only. api-handler `spawn` is stubbed in this engine build — the live agent path
  is chat sessions / **database-hook delegates**, not api `spawn`.
- **Reconciling the spec's `pubmedSearch`/`webSearch` `api:call` bindings:** there is NO
  external-binding registry in the real engine — `webSearch/webFetch/fetch` are **universal system
  globals**, not `api:call` named bindings. So the researcher does NOT need any `api:call` entry to
  search literature (it uses the universal global; grant it by OMITTING `functions:`). `api:call` is
  reserved for the app's own typed endpoints. Round 1 keeps that honest; `pubmedSearch` as a distinct
  credentialed binding is a round-2+ concern (needs the binding registry engine feature).

## Round log
### Round 1 — CORE BUILD (in progress, 2026-07-04)
- Phase 0 orient ✅ — read both architecture docs + implementation doc + health spec + engine
  source (singularizer) + blog & kitchen round-1 references + design tokens. Confirmed engine built
  through P8; `store/projects/health/` absent → fresh build. Recorded contracts above.
- Phase 1 spec improvements ✅ — folded into `app-specifications/health-application.md`:
  - **Bug fix (arch docs win):** row-type `Settings` → **`Setting`** everywhere (engine singularizer);
    added a "Row-type note (engine truth)" block enumerating Metric/LabResult/Symptom/Research/Source/Setting.
  - **+3 endpoints → 12 total:** `getSettings` (GET api/settings, find-or-creates the single row,
    seeds `tier:'free'`), `acceptDisclaimer` (POST api/settings/disclaimer), `healthStats` (GET api/stats,
    dashboard counts). Updated the api table + directory layout.
  - **+1 hook → 3 total:** added `research-deep-dive` (database on `research:insert` → `clinic/researcher#deep-dive`).
    This makes the multi-agent loop robust & engine-proven (api/interpreter writes a pending `research`
    row → a `database` hook fans it into the researcher — NO agent-to-agent delegate, exactly like
    kitchen's planner→shopper). Rewrote `requestResearch` handler to just insert the pending row (fires
    the hook) instead of relying on the stubbed api `spawn`/`delegate`.
  - **Reconciled `pubmedSearch`/`webSearch` honestly:** no external-binding registry exists → researcher
    uses the UNIVERSAL `webSearch`/`webFetch` globals (granted by omitting `functions:`), NOT an
    `api:call` binding; the credentialed `pubmedSearch` binding is deferred to round 2+. Updated the caps
    table, the frontmatter example, the Chat section, and Phases §2.
- Phase 2 PLAN ✅ — `automation/app-builder/PLAN.health.md`.
- Phase 3 build ✅ — `store/projects/health/`: 6 database schemas, 12 api handlers, 3 hooks,
  `clinic` space (3 agents: logger/interpreter/researcher), 8 pages + 8 components,
  package.json/tsconfig/.gitignore/README. Fanned out to 3 parallel Sonnet subagents by directory
  (api / pages+components / hooks+spaces+test); orchestrator wrote root+database + integrated.
- Phase 4 tests + live ✅:
  - Structural suite `tests/health.test.mjs` — **11/11 green** (`validateSchemaSet` via built
    `@lmthing/core`; 12-endpoint contract; requestResearch 402 gate; getLab include; 3 hook shapes;
    least-privilege clinic caps + per-verb table scope). Run: `node --test store/projects/health/tests/health.test.mjs`.
  - Token gate: health 16 pages/components — **0 violations** (ran the linter directly on the health
    dirs; root `lint:tokens` doesn't scan `store/projects/`).
  - **Full pipeline HTTP-verified** under `lmthing serve` (temp `LMTHING_ROOT`, health materialized,
    `LM_MODEL=S`): manifest 6 tables + **12 endpoints** + 3 hooks; `types/generated.d.ts` generated
    with all 6 row interfaces incl. **`Setting`** (not Settings); pages built (JS+CSS+index.html, 6
    routes); `GET /app/health/` → 200. API live: getSettings seeds the free row, logMetric, addLab,
    healthStats, getLab (include research), requestResearch 402 on free tier.
  - **🔴 LIVE core loop (DeepSeek `azure:DeepSeek-V4-Flash`), end-to-end** — set tier=subscription
    (admin data browser PATCH), addLab abnormal (HbA1c 9.1, refHigh 5.7 / LDL 190, refHigh 130) →
    `interpret-new-lab` database hook fired → interpreter (live) **self-query reconcile** set both
    labs `flag:'high'` and inserted **2 pending research rows (deduped)** → `research-deep-dive` hook
    fired → researcher (live) **web-searched real medical literature** (WebMD, MedlinePlus, National
    Lipid Association, Johns Hopkins, Cleveland Clinic, NCBI) and filled both `research` bodies (3936 +
    25766 chars) `status:'ready'` with a `## Sources` list + not-a-doctor line. Free-tier
    `requestResearch` → **402** (exact error contract). **Browser-verified** (chrome-devtools): labs
    list (flagged `high` badges), lab detail (nested `/labs/:id`), research page (markdown report +
    Sources + `<Chat agent="clinic/researcher">` **● Connected** over WS).
  - **Capability gate proven live**: interpreter first hit `db db:read: table "research" not
    permitted; allowed tables: lab_results, metrics, symptoms, settings` — fixed by adding `research`
    to its `db:read` scope (it must read research to dedupe pending dives). Per-verb host enforcement, live.

### Engine facts / fixes discovered this round (sdk/org)
- **`void opts` — hook-handler `delegate` DROPS structured input.** `libs/cli/src/server/routes/hooks.ts`
  `runHook` builds the handler's `delegate(agent, action, opts)` and does `void opts` ("6B carries
  structured input on its own args; opts reserved"). So a database hook **cannot thread a row id** into
  the delegated agent — the agent only gets a generic message. **Workaround (engine-correct pattern, no
  engine change): self-querying agents.** The 2 database hooks are now **declarative `trigger:`** ("reconcile
  now" signals); the interpreter re-flags ALL labs idempotently (writes only wrong flags) and the
  researcher fills ALL `status:'pending'` rows. This also absorbs insert bursts and is naturally
  loop-bounded (self-writes are UPDATEs; excluded from the insert-only hooks). This is the same lesson
  blog/kitchen imply; documented here explicitly. (A future engine improvement could pass hook `opts`
  → delegate `context`, but it's not needed and risks the shared session-manager path.)
- **🔧 ENGINE BUG FIXED (in-scope, sdk/org): SPA shell broke on depth-≥2 routes.** The built
  `index.html` used **relative** `./assets/…` URLs; on a route like `/app/health/labs/:id` the browser
  resolved them against `…/labs/` → 404 → SPA fallback → JS loaded as `text/html` → blank page (MIME
  error). Every app with a nested route was affected (blog/kitchen too — only ever API-tested). Fixed in
  `libs/cli/src/app/pages-serve.ts`: inject `<base href="/app/<project>/">` into the served SPA-fallback
  `index.html` (the pod route is always `/app/:projectId/*`, so the base is exact + prefix-safe; the
  client's `resolveAppBase` already handles router/api base at any depth — only the static asset base
  was missing). Idempotent (never doubles a `<base>`). Regression test added
  (`pages-serve.test.ts`: nested-route fallback contains exactly one `<base href="/app/health/">`).
  Full `sdk/org` gate re-run green after the fix.

### Install path used
- **Local test user** — materialized `store/projects/health/` (rsync excluding `types/ .data/
  node_modules/ tests/`) into a temp `LMTHING_ROOT`'s `<root>/health/` (the `.lmthing/` project root
  the server serves), booted `lmthing serve` (`LM_MODEL=S`), and ran the full core loop live as that
  user. No prod test user this run (local is sufficient per the task).

## Gate (round 1)
- `pnpm typecheck` ✅ (all packages) · `pnpm test` ✅ **952 passed / 21 skipped, 0 failed** (system-spaces
  included; the QuickJS "Aborted" teardown lines are the known *catchable* assertion — those tests pass)
  · health structural ✅ 11/11 · pages-serve ✅ 7/7 · `lint:tokens` health ✅ 0 violations (16 files).

## Pushed SHAs
- sdk/org `main`: **`6da8f42`** — pages-serve `<base href>` fix + regression test (pushed to origin/main).
- monorepo `main`: this commit — health app + spec + PLAN/PROGRESS + submodule pointer bump to `6da8f42`.

### Round 2 — FEATURE EXPANSION (in progress, 2026-07-04)
- Phase 0 orient ✅ — re-read both arch docs + implementation doc + health spec + PROGRESS/PLAN + engine
  space-format (Explore: project spaces load full 6-part format identically to system spaces). Baseline
  health test green (before changes). Concurrent kitchen round-2 work is uncommitted in the tree — I will
  NOT touch kitchen files; Phase-5 staging is health-only paths.
- Phase 1 spec ✅ — added a "Round 2 — feature expansion (implemented)" section to
  `app-specifications/health-application.md`: 2 new spaces (records, coaching), 8 new tables, 16 new
  endpoints, 4 new hooks, 8 new pages, extended agent caps. Documented the inline-`documents.content`
  deviation (no blob file this round; PDF/OCR deferred — needs heavier dep) + sanitisation/XSS note.
- Phase 2 PLAN ✅ — appended round-2 file-by-file plan to `automation/app-builder/PLAN.health.md`.
- Phase 3 build ✅: orchestrator authored 8 new schemas (validated: 14 tables pass `validateSchemaSet`)
  + `lab_results` personalLow/High cols + `followups` relation + 4 hooks. 5 Sonnet subagents (disjoint
  dirs): A=api(16 handlers), B=8 pages+10 components+nav, C=records space (analyst+librarian, full
  format), D=coaching space (coach, full format), E=clinic full-format remediation (functions/components/
  knowledge(3 fields×≥2 aspects)/tasklists + extended interpreter[+prep/insights/followups/baselines caps]
  & logger[+medications]). Fixed a real cap bug the E subagent flagged (interpreter inserts followups but
  db:write excluded it → added). Confirmed via engine source: actions bind tasklists ONLY via explicit
  `tasklist:` field — my hook-triggered actions omit it → run model-driven instruct prose (robust), tasklists
  are loadable decompositions satisfying full-format.
- Phase 4 tests + LIVE (DeepSeek azure:DeepSeek-V4-Flash) ✅:
  - Structural suite `tests/health.test.mjs` — **14/14 green** (14 tables via validateSchemaSet; 28-endpoint
    contract; 7 hooks; 3 full-format spaces w/ knowledge index+≥2 aspects; extended/least-privilege caps).
  - Token gate: 0 raw colors across health pages/components/space-components.
  - Full pipeline under `lmthing serve` (temp LMTHING_ROOT, LM_MODEL=S): manifest **14 tables, 28 endpoints,
    7 hooks**; types generated incl. all 8 new row types; pages built (all new routes); GET /app/health/ 200.
  - **🔴 LIVE loops verified end-to-end:**
    - **Document CSV extraction** — uploadDocument(wearable_csv) → analyze-document hook → records/analyst
      (live) `parseCsv` → inserted 5 metrics + 5 document_extractions provenance → status analyzed. ✅
    - **Document lab extraction** — uploadDocument(lab_pdf) → analyst `parseLabReport` (NEW deterministic fn
      I added after the weak model failed free-text extraction) → 4 lab_results + provenance + queued research. ✅
    - **Full cascade** document→interpret-new-lab→flag→research-deep-dive: labs flagged high/low, research
      filled status:ready. ✅ (see engine fix below)
    - **Coaching** goal-checkin → coach (live) `goalProgress` computed current=8166 from seeded steps metrics. ✅
    - **interpret** extended: created recheck **followups** for abnormal LDL/Triglycerides. ✅
    - **prep** → interpreter compiled a proper **visit brief** (flagged labs, trends via metricTrends, research,
      "Questions to ask"). ✅  **digest** → wrote **insights** (trend:steps). ✅
  - Round-1 loop regression: addLab abnormal → interpret-new-lab → flagged high (live). ✅

### Engine facts / fixes discovered this round (sdk/org)
- **🔧 ENGINE BUG FIXED (in-scope): cascaded database hooks stalled after one level.**
  `ProjectHookRuntime.drain()` (`libs/cli/src/app/hooks/runtime.ts`) — a hook-triggered agent run's own db
  writes fire `onDbWrite` WHILE the runtime is draining, so `scheduleDrain` was suppressed (`this.draining`)
  and never re-armed; the dispatcher's snapshot-up-front `drain()` never sees them → any A→B→C hook chain
  (document→interpret→research) stalled after the first level until an unrelated external write kicked a new
  drain. **Fix:** after `dispatcher.drain()` returns, `if (this.dispatcher.queued.length > 0) this.scheduleDrain()`
  — re-arms a fresh tick (still non-re-entrant; bounded by the depth cap of 3). Regression test
  `libs/cli/src/app/hooks/runtime.test.ts` (a run that enqueues a cascaded hook now completes A→B). This
  affects ALL project-apps (blog/kitchen too) — a latent bug round-1's shallower chains masked.
- **Weak-model robustness patterns applied (keep for future rounds):** (1) deterministic space FUNCTIONS beat
  model free-text/gymnastics — `parseLabReport` (lab text→rows) and `metricTrends` (group+trend) fixed
  extraction/digest/prep flakiness where DeepSeek-Flash wrote typecheck-breaking Map/sort/annotation code;
  (2) tell the model explicitly NOT to call `loadKnowledge` (knowledge is auto-injected) — it was hallucinating
  `loadKnowledge("clinical","triage","overview")` and burning turns.

### Gate (round 2)
- sdk/org `pnpm typecheck` ✅ (6/6 packages) · `pnpm test` ✅ **957 passed / 21 skipped / 0 failed** (incl. new
  runtime.test.ts; QuickJS "Aborted" teardown lines are the known catchable assertion — those tests pass) ·
  health structural ✅ 14/14 · token gate ✅ 0 violations.



### Pushed SHAs (round 2)
- sdk/org `main`: **`e4be05f`** — cascaded-hook drain re-arm fix + runtime.test.ts (pushed to origin/main).
- monorepo `main`: **`c036e3f`** — health round-2 app (113 files) + spec + PLAN/PROGRESS + submodule pointer
  bump to e4be05f (pushed to origin/main). Pointer verified == pushed submodule HEAD. Kitchen concurrent
  work deliberately NOT staged.
- Phase 6 (prod install + AI functional test) ✅ **DONE this run** (followed `.claude/skills/test-app-install-prod.md`):
  - CI built compute+store images for c036e3f (`aada091 ci: update image tags to c036e3f`); updated test pod
    `user-379847043318834826` deploy image to `compute:c036e3f`. Node was CPU-saturated (Insufficient cpu) →
    scaled 4 other user pods to 0 (370990497893738122, 380011590780479114, 380133200178996874, 380267943084189322),
    rolled the test pod, then **RESTORED all 4 to replicas=1 in cleanup (Step 8)**. Test user left installed.
  - `GET /api/apps` on the pod shows **round-2 health with all 14 tables**. `POST /api/apps/install {appId:health,force}`
    → **ok:true, 14 tables, 28 endpoints, 7 hooks, contracts.ok:true, pages.ok:true, pages.built:true**.
  - **AI functional test (real pod model, no local key):** uploaded a wearable CSV via `POST /app/health/api/documents`
    (200) → `analyze-document` hook → `records/analyst` ran the pod's live model → document `status:analyzed`,
    **2 extractions**, summary "Extracted 2 row(s) from this wearable csv document (metrics: 2)", and the **DB updated**
    (steps metric row present). Real model path fired (a 429/401 would have left it pending/error). ✅
  - **Install nuance found (not a round-2 regression; pre-existing):** re-installing an app that ADDS tables onto an
    EXISTING `app.db` did not create the new tables until a **pod restart** ran the boot schema-reconcile (then
    documents/goals/insights all 200). Workaround applied (rollout restart). Follow-up for a future engine round:
    make `POST /api/apps/install`'s reconcile step run additive `createTable` on an already-present db, not only on boot.
  - Browser UI flow (chrome-devtools) skipped: the JWT mint reads `GATEWAY_JWT_SECRET` (classifier-gated, needs a
    human `!`) — not runnable in this headless run. Server-side pod-curl proved install + build + AI + DB-update, which
    is the authoritative functional proof.

## Resume notes for the NEXT run (round 3 — FEATURE EXPANSION)
- **Round 2 is DONE, shipped, and prod-verified.** State now: **14 tables, 28 endpoints, 7 hooks, 3
  full-format project spaces (clinic, records, coaching; 6 agents), 16 pages, 20 components.** Everything
  from the spec's "Additional features" backlog is IMPLEMENTED (document ingestion + `records` space,
  visit briefs, insights/trends, personal baselines, follow-ups, wearable import, medications, coaching).
  Round 3 is strictly additive — do NOT regress/delete round-1/2 files. Floors (per round): ≥1 new space
  (→≥2 already met), ≥3 new agents, ≥5 new pages, ≥8 new endpoints, ≥3 new hooks, ≥3 new tables.
- **Round-3 backlog ideas (net-new, still inside the engine model, not-a-doctor line):** a `care-team`
  space (share a read-only summary / export a provider PDF-ish markdown; care-contacts table); a
  `medications` adherence tracker (doses table + reminder cron + interaction-check research via the
  researcher); condition/goal **programs** (multi-week plans with milestones); symptom **triage assistant**
  (a triage agent using the clinic/triage knowledge, gated, that suggests when-to-see-a-doctor as
  observations); **lab trend charts per analyte** with the personal baseline band on the labs page;
  imaging/appointment **calendar** + reminders; an **export/report** endpoint. Add ≥1 new full-format space.
- **Engine gotchas confirmed — keep applying:** (1) hook `delegate` opts are DROPPED (`void opts`) → use
  declarative `trigger:` + self-querying agents that find their own work; (2) SPA `<base href>` fix shipped
  (nested routes work in-browser); (3) `db.query` `where` is equality-only (query-all + JS filter);
  (4) `functions:` in agent instruct is space-functions-only — OMIT it to keep universal webSearch/webFetch;
  (5) an agent needs `db:read` on a table it dedupes against; (6) actions bind a tasklist ONLY via an explicit
  `tasklist:` field — omit it and the action runs model-driven instruct prose (robust for the weak model);
  (7) **cascaded db hooks now work** — the drain re-arm fix (sdk/org e4be05f) lets A→B→C chains complete;
  (8) **deterministic space FUNCTIONS beat weak-model free-text** — `parseLabReport`/`parseCsv`/`metricTrends`
  fixed extraction/digest/prep; tell the model NOT to call `loadKnowledge` (auto-injected) or it flails;
  (9) run the app via temp `LMTHING_ROOT` + `POST /app/health/api/*` + admin browser
  (`GET/PATCH /api/projects/health/app/data/:table[/:id]`) + `POST .../hooks/:slug/run`.
- **Prod test-app-install nuance:** re-installing an app that adds tables onto an existing `app.db` needs a
  pod `rollout restart` to run boot schema-reconcile before the new tables exist (see Phase 6). Consider
  fixing the install-endpoint reconcile in a future engine round.
- Researcher output quality: DeepSeek-Flash still occasionally pastes scraped content despite the
  "summarise in your own words" guardrail — tighten further / try a stronger research model when available.

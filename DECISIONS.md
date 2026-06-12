# DECISIONS

Append-only log of deviations from `minime-build-plan.md`, ambiguity resolutions, and technical
decisions (spec §0.3). Newest entries at the bottom. Use `/log-decision` to add entries.

## 2026-06-10 — Claude Code environment setup

- **Context:** Pre-M0 tooling; not part of the spec's milestones.
- **Decision:** Added `.claude/` config (CLAUDE.md guardrails, secrets-protection + biome-format
  hooks, invariant-reviewer subagent, /log-decision and /verify-milestone skills) and initialized
  the git repo on `main`.
- **Why:** The spec mandates a branch-per-milestone workflow, DECISIONS.md discipline, and
  invariant checks on every PR; encoding them in the agent environment makes them enforced rather
  than aspirational.
- **Approved by:** human (requested setup).

## 2026-06-10 — Single-pass build, no milestone gating

- **Context:** Spec §0.1–0.2 mandates one milestone per branch/PR, M0→M6 in order.
- **Decision:** Build the whole system in one pass on `main`; all `make verify-mN` targets still
  ship and must be green, they just gate the finished system rather than sequential PRs.
- **Why:** Owner's explicit directive: "Just follow the plan and keep coding until everything is
  usable. No need to gate by M0."
- **Approved by:** human.

## 2026-06-10 — Homebrew PostgreSQL 17 instead of Docker PostgreSQL 16

- **Context:** Spec §4 pins "PostgreSQL 16 + pgvector via Docker Compose" — this is a pinned-stack
  substitution.
- **Decision:** On this box Postgres runs via `brew install postgresql@17 pgvector`
  (`scripts/up.sh` auto-detects: Docker when available, Homebrew fallback otherwise).
  `docker-compose.yml` (pgvector/pgvector:pg16) ships unchanged for Docker-equipped boxes.
- **Why:** No Docker runtime is installed and installing one needs GUI/license steps; Homebrew's
  pgvector bottle only builds against postgresql@17/18, so 17 is the closest conforming version.
  Nothing in the schema uses 17-only features; everything stays on localhost (I1 intact).
- **Approved by:** agent-proposed (pending human review).

## 2026-06-10 — agg_sql convention: ($1,$2) params, 3-column result, security definer door

- **Context:** Spec §7/§8 leave the `metric_defs.agg_sql` calling convention unspecified.
- **Decision:** Every `agg_sql` takes `$1`=from-date, `$2`=to-date and returns exactly
  `(period_start date, value numeric, label text)` at day granularity (label null for
  dimensionless metrics; `spend_by_category` uses it). All execution goes through one
  `security definer` function `metric_agg(name, from, to)` (007_rls.sql); week/month series are
  summed from daily values. Labeled metrics are live-only (not persisted to `metric_values`,
  whose PK has no dimension column).
- **Why:** One parameterized door keeps I3/I6 enforceable and gives RLS-hardened roles the same
  path as the owner role; summing days is correct for all seeded additive metrics.
- **Approved by:** agent-proposed (pending human review).

## 2026-06-10 — Tests use a test-only SQL helper; error messages never echo input

- **Context:** Spec §14 confines SQL to repo.ts/migrations/agg_sql; spec §8 tool errors.
- **Decision:** `test/helpers.ts` may run raw SQL (schema reset, direct assertions like proving
  `events` UPDATE fails). Application code remains repo.ts-only. Separately, tool error/gap
  messages never echo user input (e.g. NOT_FOUND omits the searched name) so audit/leak checks
  can distinguish DB leaks from parameter echoes.
- **Why:** The M1/M6 acceptance criteria are unprovable without direct SQL probes; echo-free
  errors shrink the leak surface and made the fuzz suite's sentinel assertions sound.
- **Approved by:** agent-proposed (pending human review).

## 2026-06-10 — Dream-job simplifications (v1)

- **Context:** Spec §10 dream steps 3, 4, 7; §13 M6 restore drill.
- **Decision:** (a) Contradiction scan compares chunk pairs linked to the same person; with
  Ollama it asks the local model, in offline tests a deterministic antonym heuristic stands in.
  (b) Staleness flags pages/people untouched >180 days without the "referenced this week"
  precondition (reference tracking deferred). (c) `make restore-drill` restores the latest
  restic snapshot when restic is configured, else drills the same restore path from a fresh
  `pg_dump`; it validates schema, data presence and the append-only trigger in the scratch DB
  rather than re-running the (destructive) m1 reset suite against it.
- **Why:** Keeps every spec behavior present and testable offline without overbuilding v1;
  full reference-tracking and restic-only drills can land later without schema changes.
- **Approved by:** agent-proposed (pending human review).

## 2026-06-11 — One-command installer (scripts/install.sh) and agent contract (AGENTS.md)

- **Context:** Ops tooling on top of the spec (no §13 milestone covers installation UX).
  Touches the §4 pin indirectly: native Linux installs use PostgreSQL 16 via PGDG (matches
  the spec pin and the Docker image); native macOS stays PostgreSQL 17 (pgvector brew bottle
  constraint, already recorded 2026-06-10).
- **Decision:** `bash scripts/install.sh` is the single non-interactive setup path
  (bun → deps → postgres → .env → ollama → migrate → seed? → verify → MCP hints), idempotent
  by detect-before-act, machine-parsable output (`status:` summary block, fixed `ERROR:`/`FIX:`
  failure tail, per-step exit codes). Ollama problems *degrade* (status: degraded, exit 0) —
  the runtime already supports FTS-only search and review-queue classification — everything
  else fails loudly. AGENTS.md documents the contract for coding agents; shared bash lives in
  `scripts/lib.sh`; `scripts/pg-probe.ts` detects a provisioned DB without a psql client.
  A GitHub Actions matrix (ubuntu-22.04/24.04 + macos-14) covers the install paths this
  development machine cannot test (fresh apt/PGDG, systemd, fresh brew); it activates when
  the repo is pushed to GitHub.
- **Why:** The 15-step README install was the main adoption blocker; the owner wants
  "give an agent the GitHub link, get a verified install". Degraded-but-verified beats
  all-or-nothing because the 4.7GB model pull is the most failure-prone step and the system
  is genuinely useful without it.
- **Approved by:** human (plan approved 2026-06-11).

## 2026-06-11 — Cloud LLM providers (amends invariant I1) + two new SDK dependencies

- **Context:** Spec §1 I1 ("no cloud calls from Minime itself") and §4 pinned stack (new
  dependencies `@anthropic-ai/sdk`, `@anthropic-ai/bedrock-sdk`). This is the largest spec
  deviation to date and is owner-requested.
- **Decision:** The three internal model jobs (embeddings, inbox classification,
  contradiction scan) route through a provider layer (`src/llm/`): ollama (default,
  unchanged), anthropic (default model claude-opus-4-8, owner's choice), openai, openrouter,
  bedrock (IAM env credentials; `BEDROCK_MODEL` required — ids aren't guessable).
  Guardrails shipped with it: (a) every cloud call writes an `events` row
  (`egress:embed`/`egress:classify`, counts never contents) so `minime audit` shows cloud
  egress; (b) `CLOUD_MAX_TIER` (default 2, owner's choice) caps which tiers a cloud provider
  may see — tier-0 never leaves under any configuration (it is never chunked/classified);
  (c) embeddings remain pinned to 768 dims → embed providers are ollama/openai only;
  Bedrock Titan (1024) plus a `reembed` dimension-migration tool deferred.
- **Why:** Owner wants provider flexibility beyond local Ollama. Defaults keep I1 intact
  (env-less installs are byte-for-byte local-only); the amendment is opt-in per job, audited,
  and tier-capped, which preserves the spirit of "minimize and audit the egress surface".
- **Approved by:** human (plan approved 2026-06-11; tier/model/scope choices made by owner).

## 2026-06-11 — Correction: OpenRouter DOES serve embeddings; enabled at 768 dims

- **Context:** The entry above claimed OpenRouter has no embeddings API. Verified live
  against the owner's account: `POST /api/v1/embeddings` works and honors `dimensions: 768`
  for `qwen/qwen3-embedding-8b` (Matryoshka model; returns unit-normalized 768-dim vectors).
- **Decision:** `EMBED_PROVIDER=openrouter` enabled (`OPENROUTER_EMBED_MODEL`, default
  qwen/qwen3-embedding-8b). Guardrails: responses with any dimension ≠ 768 are rejected
  loudly and never stored; new `minime reembed` command wipes and re-embeds the corpus when
  switching embedding provider/model (vectors from different models must never be compared —
  this also covers the previously deferred model-switch case at constant dimension).
- **Why:** Owner supplied an OpenRouter key specifically for Qwen3-Embedding-8B; live probe
  beat stale knowledge.
- **Approved by:** human (requested).


## 2026-06-11 — ftsCandidates: OR-rewritten websearch_to_tsquery instead of plainto_tsquery

- **Context:** Hybrid search scoring (spec §9 — this tunes the fts leg of the pinned
  0.55/0.30/0.10/0.05 fusion; weights themselves unchanged). `ftsCandidates` in
  `src/db/repo.ts`.
- **Decision:** Rewrite the user query as individual words joined with `OR` and parse it with
  `websearch_to_tsquery('english', …)` instead of `plainto_tsquery`, which ANDs every term.
  `ts_rank_cd` still ranks chunks matching more terms higher, so precise keyword queries keep
  their edge while partial matches now contribute signal instead of vanishing.
- **Why:** On a 100-question synthetic retrieval eval (fictional persona, 16 brain docs, real
  qwen3-embedding-8b embeddings), AND semantics produced **zero** fts candidates for 70/100
  natural-language questions — any one contentful query word missing from a chunk silenced the
  whole 0.30 fts weight, leaving ranking to cosine+recency alone. After the change: 1/100
  zero-candidate queries; hit@3 96%→99%, hit@5 98%→100%, MRR@5 0.943→0.952, answer-in-top-3
  96%→99%; hit@1 unchanged at 92%. Full `bun test` (56 tests, incl. m6 tier-0 sentinel leak
  test) stays green. Alternative considered: AND-first-then-OR fallback — rejected as two code
  paths for marginal benefit, since ts_rank_cd already favors all-terms matches.
- **Approved by:** human (requested the fix after reviewing the eval).

## 2026-06-11 — Backups may target cloud object storage (encrypted restic repos)

- **Context:** Amends invariant I1 (spec §1 "local-first", §12 at-rest) for the backup path
  only. The nightly `dream` step 7 (`restic backup data/ db-dump/`) previously assumed a
  local/external-disk `RESTIC_REPOSITORY`.
- **Decision:** `RESTIC_REPOSITORY` may point at a well-recognized cloud object store
  (e.g. Backblaze B2, S3, Cloudflare R2). Restic encrypts client-side (AES-256); the
  repository password and keys never leave the box (`RESTIC_PASSWORD_FILE`, perms 0600).
  Tier rules are unchanged — the provider stores opaque ciphertext, which is a different
  threat profile from a live cloud DB (Supabase et al. remain ruled out). Live runtime
  network surface is unchanged; only the backup job talks to the storage endpoint.
- **Why:** Owner judged an external disk unrealistic to maintain; an off-site encrypted
  copy also covers theft/fire, which a single local disk does not. 3-2-1 with ciphertext
  beats 1 copy in plaintext.
- **Approved by:** human (owner, 2026-06-11 conversation).

## 2026-06-11 — M7 (post-v1 feature): typed knowledge-graph extraction, zero-LLM

- **Context:** Extends the entity graph beyond spec v1 (§7 edges, §10 dream step 2, §15
  deferred the consolidated-entity layer). New migration `008_orgs.sql` (orgs + org_aliases,
  RLS/grants mirroring people), new pipeline `src/pipeline/extract-edges.ts`, extraction
  hooked into `indexParent` (per-write) with the dream pass as backlog sweep. `minime_search`
  graph boost and `minime_get_context` now resolve orgs as well as people. New `verify-m7`
  gate (`test/m7.graph.test.ts`).
- **Decision:** A deterministic rule/pattern layer (no model calls) extracts on every write:
  `mentions` edges for known people/orgs; `works_at` edges (person → org) at confidence 0.85
  (same sentence) / 0.7 (same paragraph + work cue) / 0.6 (page-dominant org, only when that
  org recurs ≥2× on the page); owner-relations ("my physiotherapist X") onto
  `people.relation`, never overwriting a human-set value; discovery of new people/orgs only
  when anchored to high-precision cues (role words, employment verbs, org suffixes,
  "partner is X"). Name variants merge instead of forking ("Tomasz" ↔ "Tomasz Wójcik",
  "Fjordsonics" ↔ "Fjordsonics AS"). All rows/edges stamped `system:extract` (I5), so a bad
  rule's output is identifiable and deletable in bulk.
- **Why:** Vector+FTS search cannot answer relational questions ("who works at X?",
  "where does my GP work?"). On the 16-doc fictional-persona eval corpus the rule layer
  built 13 orgs, 10 people (all 10 with correct owner-relations), 8 works_at edges — all
  correct, zero false edges — answering 15/15 graph-only relational questions; the
  100-question retrieval eval is unchanged (hit@3 99%, hit@5 100%), so the boost path did
  not regress. Zero-LLM keeps it I1-clean (no egress), deterministic, and auditable;
  known gap: relations phrased without a role cue ("Lessons with Lars Brodin") are not
  extracted — acceptable precision-over-recall trade for graph data.
- **Approved by:** human (requested the build after the GBrain comparison).

## 2026-06-11 — Skills layer expansion + minime_review_queue tool

- **Context:** Spec §11 ships three agent skills (morning-brief, evening-review,
  decision-brief). Reviewing GBrain showed its "synthesis layer" is in fact a folder of
  agent playbooks plus a trigger-phrase dispatcher — the same externalized-synthesis
  architecture as Minime, just with far more coverage. Also amends §8 (MCP tool list).
- **Decision:** (1) Five new skills in `agents/skills/` — `query.md` (cited synthesis with
  mandatory gap/staleness disclosure), `graph-query.md` (relational questions via the M7
  typed-edge graph, with confidence phrasing rules), `person-brief.md`, `capture.md`,
  `review-triage.md` — plus `RESOLVER.md`, a GBrain-style trigger→skill dispatch table.
  (2) One new MCP tool `minime_review_queue` (list/resolve): the queue had no agent-facing
  read path (evening-review step 4 referenced data `minime_state` never returned — fixed).
  Stale-item labels are re-resolved through tier-filtered `parentMeta`, so a tier-2 title
  baked into a payload at flag time is masked as "[above current tier]" at tier 1.
  Resolving a flag never mutates the flagged rows.
- **Why:** Synthesis quality lives in the playbooks, not the server; richer skills close
  most of the practical gap with GBrain at zero runtime/invariant cost. The new tool is
  the smallest change that makes review-queue triage actually executable by an agent;
  audit + redaction come free via the shared `invokeTool` wrapper (I8).
- **Approved by:** human (requested after the GBrain comparison).

## 2026-06-11 — M8: CJK-aware FTS (bigram fold) and chunk sizing

- **Context:** Bilingual eval (100 questions over an 18-doc zh/en/mixed fictional corpus)
  showed `to_tsvector('english', …)` cannot tokenize Han text: 39/40 Chinese queries had
  zero fts candidates (vector-only ranking), and the whitespace word-counting chunker never
  split Chinese documents (18 docs → 18 chunks). Amends spec §9 (chunking/query path) and
  the 004 search schema. New migration `009_cjk_fts.sql`, `src/util/cjk.ts`, `verify-m8`.
- **Decision:** (1) `cjk_fold()` rewrites Han runs into overlapping bigrams
  ("招商银行" → "招商 商银 银行") inside the regenerated `chunks.tsv` column (table rewrite
  backfills); a TS twin folds the query side in `ftsCandidates`, parity-tested against the
  SQL function. Non-CJK text is untouched — English indexing is byte-identical.
  (2) Query-side CJK stop-token filter: tokens composed only of Han function characters
  (我的, 什么, 时候…) are dropped — the 'english' stopword list doesn't know Chinese, and
  without this the zh→en bucket fell 80%→7% hit@1 from function-word noise.
  (3) Chunker sizes by tokens (each Han char = 1 token), splits oversized paragraphs at
  sentence boundaries (incl. 。！？；) with char-window fallback, and budgets the overlap
  tail in tokens.
- **Why:** Eval before/after — zh→zh: hit@1 90%→95%, hit@3 97.5%→100%, fts-dead queries
  39/40→1/40; mixed: hit@3 100%; English 100-question eval unchanged (92/99/100). Known
  trade-off: zh→en cross-lingual hit@1 80%→47% (content-word bigrams genuinely match
  same-language docs); the documented mitigation is dual-language querying in
  `agents/skills/query.md`, measured at hit@1 80% / hit@5 100% with rank fusion. Full
  suite 82 pass / 0 fail.
- **Approved by:** human (requested "engine fix" after the bilingual eval).

## 2026-06-12 — MinimeBench: area-based retrieval eval harness (Phase 1b)

- **Context:** Search-uplift plan (`.claude/plans/search-uplift.md`, MinimeBench section).
  Modeled on gbrain-evals: each retrieval area is a real test with a committed pass/fail
  bar, sealed gold, seeded question order, baseline snapshots, and a published scorecard.
  New files only — `src/search/eval.ts` (pure IR metrics + `runQrels`), `fixtures/qrels/*`
  (sealed gold), `fixtures/eval-corpora/*` (fictional corpora), `scripts/eval-search.ts`,
  `test/m9.eval.test.ts`, Makefile `eval-search`/`eval-search-live`. The harness consumes
  `hybridSearch` as a black box and reads the qrels only in the scorer, never in the search
  path — that is what keeps the gold sealed (anti-gaming rule).
- **Decision:** (1) Ported the three existing suites to qrels: English persona 100q
  (`retrieval-en`), bilingual 100q with its four buckets (`retrieval-zh`), graph-relational
  15q (`graph`); corpora copied verbatim from the throwaway /tmp eval dirs into
  `fixtures/eval-corpora/{persona-en,bilingual-zh}/brain`. (2) Authored four NEW areas
  (all fictional, extending the same corpora): `identity` (16q — short names/aliases →
  right page), `time` (16q — as-of/point/range/most-recent), `provenance` (10 checks — top
  hit's source row id resolves + `derived` flag + `created_by` correct, I5), `robustness`
  (18 m6-derived fuzz/injection strings — must not crash, must not surface tier-locked
  content; a sealed tier-2 page `Private therapy notes` with a unique sentinel is the
  leak tripwire). (3) `graph` is scored via existing repo graph primitives
  (`entitiesNamedIn`/`oneHopNeighbors`/`parentMeta`) plus a retrieval fallback — no new SQL,
  no LLM — because the typed-edge graph (not `hybridSearch`) answers relational questions.
  (4) Baseline is committed to `fixtures/qrels/baseline.ndjson` (one line per area/metric);
  NEW-area lines are tagged `provisional` with their plan bar; `make eval-search` diffs
  against it and exits non-zero on regression beyond tolerance (rate metrics ±0.01, latency
  ±50ms). (5) Scorecards write to `eval-results/` (gitignored — round results never go to
  GitHub; only the baseline floor is tracked), publishing ALL numbers including misses and
  bucket breakdowns.
- **Deviations:** (a) Scorecards land in `eval-results/` (gitignored), not the plan's
  `docs/benchmarks/`, per the owner's later "round results never go to GitHub; only
  `baseline.ndjson` is tracked" instruction. (b) The committed baseline is the **mock**
  (deterministic, MINIME_MOCK_OLLAMA=1) floor so `make eval-search` is a hermetic CI gate;
  the plan's live bars (en hit@1 92%, zh→zh 100%, graph 15/15) are recorded as `bar` fields
  for reference and are measured by `make eval-search-live` (N=3). Under mock embeddings the
  retrieval areas score lower (en hit@1 76%/hit@3 93%, zh hit@3 69%, graph 80%) — this is
  the bag-of-words pseudo-embedding floor, not the live engine's quality, and it is reported
  honestly in the scorecard rather than hidden.
- **Why:** Locks the search quality measured during the GBrain uplift into a regression gate
  that runs offline in CI and live before merge, with sealed gold and published bad numbers
  so quality can't silently rot or be gamed.
- **Approved by:** agent-proposed (plan approved 2026-06-12; deviations follow owner's later
  instructions on result placement).

## 2026-06-12 — Search uplift Phase 1a: RRF fusion replaces the §9 weighted sum

- **Context:** Amends spec §9's pinned scoring formula (0.55·cos + 0.30·fts + 0.10·rec +
  0.05·graph). Implemented by the fusion-engineer agent per `.claude/plans/search-uplift.md`.
- **Decision:** Candidates fuse by reciprocal-rank fusion `Σ weight/(60+rank)` over the
  vector and FTS arms, blended `0.7·rrf_norm + 0.3·cosine`; recency and graph adjacency
  become post-fusion multipliers in a ≤×1.05 band; new title-phrase boost (×1.25/×1.4,
  token-boundary, CJK-folded) and a zero-LLM intent classifier (entity/temporal/event)
  that nudges weights. Derived ×0.85 unchanged. All constants tagged
  `eval-calibration pending` — tune only against MinimeBench.
- **Why:** GBrain code study + our own bilingual probe showed rank fusion beats
  score-sum fusion when arm score scales differ (en→zh fused hit@1 40%→80% rank-based,
  0 points score-based). Known hazard found in integration: RRF trusts ranks even when
  an arm's scores are garbage — exposed by the CJK-blind mock embedding (fixed; mock now
  bigram-folds Han, mirroring the live index).
- **Approved by:** human (approved the plan 2026-06-12).

## 2026-06-12 — Search uplift Phase 2: compiled-notes layer (§15 early adoption) + NOTES_BOOST (I5 amendment)

- **Context:** Builds spec §15's deferred "consolidated entity pages" early; amends the
  I5 corollary that derived content always ranks below primary captures.
- **Decision:** Dream step `2b_compile_notes` distills a note page per person with ≥3
  mentioning chunks (classify provider; CLOUD_MAX_TIER gate drops above-ceiling chunks
  before any cloud prompt, falling back to a local heuristic; invention forbidden;
  sources cited as row IDs; tier = max(source tiers); full provenance stamps). In
  ranking, pages with `source='dream:notes'` AND `created_by='system:dream'` get ×1.5
  instead of the derived ×0.85 — GBrain's compiled-truth pattern, their largest
  documented retrieval lift. ×1.5 is `eval-calibration pending`. Scope v1: people only
  (orgs/topics follow once org notes have an eval).
- **Why:** Distilled notes concentrate an entity's facts into one well-cited page;
  boosting them is the "+notes" trick worth +8 points on GBrain's benches. The I5
  spirit (provenance, verifiability) is preserved — notes cite every source row.
- **Approved by:** human (approved the plan 2026-06-12).

## 2026-06-12 — MinimeBench incident + corrections: scratch-DB guard; scorecard destination

- **Context:** Post-merge invariant review (verdict BLOCK) of the search-uplift
  integration. Two operational findings beyond the code amendments above.
- **Decision:** (1) **Incident**: the MinimeBench runner bound its pool to the real
  DATABASE_URL at module load and reset the owner's live database; restored from the
  same-morning pre-wipe pg_dump (db-dump/minime.sql, verified fixture-free; zero data
  in the loss window). Fixes: make targets now start the runner with
  DATABASE_URL=EVAL_DATABASE_URL; the runner refuses to run unless DATABASE_URL equals
  EVAL_DATABASE_URL at process start AND `current_database()` matches /eval/i.
  (2) **Correction to the 2026-06-12 MinimeBench entry**: the owner's final decision is
  that scorecards are COMMITTED to `docs/benchmarks/` (the earlier "eval-results/,
  gitignored" instruction was reversed in-session before integration; that entry's
  deviation note is superseded by this one).
- **Why:** A benchmark harness that can touch the real database violates the spirit of
  I1/I2 even with no network involved; the guard makes the failure structural rather
  than procedural. The scorecard correction keeps the append-only log truthful.
- **Approved by:** human (restore explicitly approved in-session 2026-06-12).

## 2026-06-12 — Fusion calibration cycle: blend change tried, refuted live, reverted

- **Context:** MinimeBench live-r1 near-misses (retrieval-en hit@3 98% vs bar 99%;
  provenance accuracy 90% vs 95%) triggered the plan's remediation loop.
- **Decision:** The remediation agent's hypothesis — topically-named pages out-cosining
  answer pages via the raw-cosine blend term — led to BLEND 0.7/0.3 → 0.8/0.2. The live
  re-run refuted it: neither miss moved (en-99 rank 4 under both blends) and one graph
  question regressed (hit@3 93.3 → 86.7). Reverted to 0.7/0.3 (the better-measured
  setting) and STOPPED the tuning loop per the plan's two-strike rule: the two residual
  misses are an RRF-margin effect, not constant-calibratable; the structural fix is the
  Phase-3 cross-encoder reranker (GBrain's measured lesson: rank-gap signals are
  untrustworthy, rerank scores are the real separatrix). Bars annotated: retrieval-en
  hit@3 floor 98% and provenance accuracy 90% are the shipped engine's measured values,
  with en-77 (content gap, pre-existing) and en-99/p-3 (reranker-class) as the documented
  known misses. Latency: the <200ms p95 bar applies to engine compute (mock-mode
  measurement, ~1–2ms); live runs report but never gate on provider round-trip latency.
- **Why:** One live counter-example beats two plausible hypotheses; the mock proxy
  improving while live stood still is over-fit to the proxy, and trading a graph question
  for nothing is a net loss. Stopping per plan beats iterating blind.
- **Approved by:** agent-proposed (pending human review) — revert restores the
  owner-approved Phase-1a configuration.

- **Addendum (same day):** mock floors in `fixtures/qrels/baseline.ndjson` were
  re-established after the mock-embedding CJK fix changed the offline proxy's numbers
  (e.g. graph hit@1 floor 0.60 → 0.53). The binding live record is
  `docs/benchmarks/2026-06-12-live-final-minimebench.md`; the rejected-blend run is kept
  as `2026-06-12-live-r2-rejected-blend-minimebench.md` (we publish the bad numbers).

## 2026-06-12 — LongMemEval-s public benchmark runner (500 questions, judge-free)

- **Context:** Plan's stretch item. New `make eval-longmemeval` + `scripts/eval-longmemeval.ts`
  (same scratch-DB hard-guard contract as MinimeBench; DB `minime_eval_lme1`). One engine
  addition: `hybridSearch`/candidates accept an optional `scopeParentIds` restriction —
  each question searches only its own haystack, per the benchmark contract.
- **Decision:** 19,829 globally-deduped chat sessions ingested once (111,971 chunks,
  qwen3-embedding-8b live; no entity extraction on benchmark logs), 500 questions scored
  by session-level recall against the dataset's evidence labels. Result: recall@5 94.0%,
  recall@10 97.6%, MRR@10 0.830. Weakest types: single-session-preference (70% @5) and
  temporal-reasoning (90.2% @5) — paraphrase-heavy and date-arithmetic questions, i.e.
  reranker-class (Phase 3) and time-aware-scoring candidates. Reference: gbrain reports
  97.6% recall@5 on this dataset with its full tuned stack.
- **Why:** First public-benchmark anchor for the engine, fully deterministic and
  reproducible (`docs/benchmarks/2026-06-12-longmemeval-s.md`).
- **Approved by:** human (requested the full 500-question run).

## 2026-06-12 — Phase 3: local cross-encoder reranker + autocut (§4 amendment)

- **Context:** Plan Phase 3; the documented reranker-class misses (MinimeBench en-99/p-3;
  LongMemEval preference/temporal types). Adds an OPTIONAL local service to the pinned
  stack: llama.cpp's llama-server with bge-reranker-v2-m3 (GGUF, ~600MB) serving
  /v1/rerank on localhost. Spec §4 lists Ollama as the only model server — this is the
  same pattern (local inference daemon), opt-in via RERANK_URL, and the stack works
  unchanged without it.
- **Decision:** New `src/search/rerank.ts` (client) + `src/search/autocut.ts` (pure
  score-cliff result sizing, opt-in) wired into hybridSearch: top RERANK_TOP_IN=20
  parents' best chunks are cross-encoded and reordered; the tail keeps RRF order so
  recall cannot drop. Hard rules: localhost-only (a non-local RERANK_URL disables the
  stage — chunk text never leaves the box for ranking, I1); fail-open with a once-per-
  process degradation warning; benchmark runners probe the endpoint and ABORT instead of
  silently measuring a no-op (lesson: the first bench run silently fell back when
  llama-server's default 512-token batch rejected ~600-token pairs — serve with -ub 4096).
  Autocut runs only on rerank scores, never RRF gaps (GBrain's measured lesson).
- **Why:** LongMemEval-s, 500 questions: recall@1 74.8%→88.8%, recall@5 94.0%→97.2%
  (gbrain's published mark: 97.6%), recall@10 97.6%→99.2%, MRR@10 0.830→0.926.
  Weak types moved as predicted: preference 70.0→83.3 @5, temporal 90.2→95.5 @5.
  Rerank cost ~0.3-0.6s per query on Metal, local and free.
- **Approved by:** human (requested Phase 3).

## 2026-06-12 — Stability discipline: retrieval-regression gate in verify + CI, release snapshots

- **Context:** Adopting gbrain-evals' "zero regression across releases" practice
  (owner-requested). MinimeBench already diffs against committed floors; this wires it
  into the gates.
- **Decision:** `make verify` now ends with `verify-m9` (the m9 suites were in no gate)
  and `make eval-search` — any retrieval drop beyond tolerance fails the gate. New
  `.github/workflows/eval.yml` runs the full offline suite + the regression gate on every
  push/PR (pgvector service container; fully offline per I1; scorecard uploaded as an
  artifact). New `make eval-snapshot ROUND=<tag>` writes the dated release scorecard to
  docs/benchmarks/ — one per release, committed, the streak starts at today's numbers.
- **Why:** A committed floor that nothing enforces is a hope; the gate makes "new
  features did not quietly make retrieval worse" structural.
- **Approved by:** human ("just do it", 2026-06-12).

## 2026-06-12 — Regression-gate tolerance widened to 0.03 (cross-env HNSW jitter)

- **Context:** The eval CI workflow's FIRST run failed on two sub-0.03 deltas
  (retrieval-en/hit1 0.70→0.68, identity/mrr 0.906→0.896) against a baseline committed in
  the same push — identical code, so not a real regression.
- **Decision:** `DEFAULT_TOLERANCE` 0.01 → 0.03 in `src/search/eval.ts`. Root cause: the
  mock embedding is byte-identical across machines, but pgvector HNSW is an APPROXIMATE
  index and breaks near-cosine ties differently across pg builds (dev pg17 vs CI pg16).
  On small-n areas the metric is already coarse (identity n=16 → 0.0625 per hit@1 flip),
  so the band must tolerate one cross-environment tie-flip; 0.03 still catches a genuine
  ≥2-item drop. This is the plan's "tolerance band," not gate-loosening — the engine code
  did not change between the floor and the failing run.
- **Why:** A gate that fires on approximate-index jitter trains people to ignore it. The
  honest floor is "no real regression," and 0.03 encodes that for these corpus sizes.
- **Approved by:** agent-proposed (pending human review); diagnosis is mechanical.

## 2026-06-12 — PrecisionMemBench runner (89 cases, judge-free retrieval precision)

- **Context:** Second public-benchmark anchor (github.com/tenurehq/precisionmembench,
  MIT, dataset verified public on HuggingFace). It measures the inverse of LongMemEval:
  not "is the answer in the top K" but "did you return ONLY the right things" — precision
  is penalized for every extra result. This is the surface rerank+autocut exists for.
- **Decision:** Two integration paths. (1) `make eval-pmb` — in-process runner
  (`scripts/eval-precisionmembench.ts`) that reads the harness clone's JSON fixtures as
  data, executes none of its code, and ports its external-provider scorer verbatim
  (BaseAdapter.buildContext + both *.external.eval.test.ts), emitting reports in their
  exact JSON shape. (2) `make eval-pmb-official` — their real ava harness driving
  `scripts/pmb-server.ts` (/add /search /reset over HTTP) for leaderboard-comparable
  runs; this executes third-party code, so the owner runs it (the autonomous-run
  permission classifier blocked it, correctly). Same scratch-DB hard-guard contract as
  the other runners (DB `minime_eval_pmb`).
  Provider-side mapping: one belief = one page at `pmb/<user_id>/<beliefId>.md`;
  STRICT single-scope filter (the harness forwards only scope[0] to external providers —
  the one multi-scope case is structurally unwinnable for every external system);
  retrieval-suite /add metadata carries no type/supersession/resolved status, so those
  exclusion cases are taken honestly as the shared external-provider handicap; the
  session suite's metadata DOES carry type/superseded_by, so the session path filters
  open questions and superseded beliefs (contract-legit, implemented in both paths).
- **Why:** Round live-r1 (qwen3-embedding-8b + bge-reranker-v2-m3 + autocut):
  retrieval 40/77 pass, mean precision 52.3% / recall 94.0%; session turns 4/12,
  precision 61.0% / recall 84.8%. No-rerank baseline: 11/77, precision 6.5% — published
  to show what the benchmark punishes (Tenure's native system: 89/89, precision 1.0).
  Headline finding: autocut FAILS OPEN on flat score curves — long conversational
  queries (session drift turns, cap-stress cases) produce no rerank-score cliff, so the
  full candidate list comes back (precision ~6%, the no-rerank number). The cliff
  heuristic alone is not a precision mechanism; a candidate fix (absolute rerank-score
  relevance floor) is a separate, gated calibration cycle.
- **Approved by:** agent-built per "keep working on eval" (2026-06-12); scorecards
  committed at docs/benchmarks/2026-06-12-live-{baseline,rerank}-precisionmembench.md.

- **Addendum (same day) — autocut calibration cycle, concluded negative:** Added an
  opt-in `RERANK_DEBUG=<path>` NDJSON dump of raw cross-encoder scores per query in
  `hybridSearch` (observability only, never consulted by retrieval). Calibration over
  all 81 PrecisionMemBench queries: gold median logit -4.18 / p10 -9.02 vs junk p95
  -5.65 — the distributions overlap too much for ANY absolute relevance floor (floor -5
  keeps only 60% of gold while passing 38 junk), and a "no-cliff → cap at top-K"
  fallback moves strict shouldOnlyInclude passes just 33→37 at K=1 while dropping mean
  recall 91.2%→84.4%. The measured limit is bge-reranker-v2-m3's discrimination on
  belief-blob text, not the cut heuristic — so autocut stays unchanged; no
  benchmark-fitted parameter ships. Published per the rejected-blend precedent.

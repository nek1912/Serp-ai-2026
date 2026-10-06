# Project Status

**This is the one file every AI session and every team member reads first.**
The actual code files are the ground truth. This file reflects what is
currently implemented and working. When in doubt, read the code.

Update this at the end of every work session. An out-of-date status file is
worse than none — the next session will trust it.

---

## Last updated

`2026-10-06` — **rag-fix merged to main + backend FROZEN FOR HACKATHON DEMO + `backend/.env` single source of truth.** `rag-fix` (static 6-key RPC + `as_of_date` threading, grounding enforcement with repair→re-verify→abstain, PACS prompt fix, insurance-keyword fix, citation URL allowlist + marker normalization + full `web_*` IDs, Gemini reranker 10s floor) merged as `403b9de`; the 2 same-hunk conflicts (`retrieval/__init__.py`, `services/static_rag.py`) resolved toward `rag-fix` (superset of `main`'s independent same fix). `backend/.env` is now the only backend config source (absolute path; repo-root `.env` ignored with warning). Full suite: **1434 passed / 83 failed** (same 83 pre-existing baseline files, zero new failures); ruff clean; live smoke A–J passed incl. MSCS HIGH 1.0 with 23 valid citations. Accepted risks: provider variance, no INSURANCE grievance category, Sarvam code-mixing. No more feature/architecture changes before the demo.

`2026-10-06` — **WebRAG timeout-lifecycle fix (cooperative deadline) + frontend 503 fix + full-suite re-baseline.** (1) Live demo found WebRAG computing a strong result (8 chunks, top 67.2) AFTER the orchestrator's 45s `wait_for` had fired: `task.cancel()` does not stop the `to_thread` worker, and `retrieve()` had no budget notion, so recovery ran past the timeout and the late result was discarded (`web=0 chunks` → human-verification abstain). Fix: `WebRAGService.retrieve(..., deadline)` — initial attempt always runs, no NEW recovery round starts past `started + web_rag_timeout_s` (passed by orchestrator on web-only + dual paths), `metadata["deadline_stopped_recovery"]` stamped; thresholds/RRF/BM25/verifier/branches/2-round bound untouched. New `backend/tests/test_web_rag_deadline.py` (8 tests). (2) Fixed `POST /api/chat/stream` 503: `BACKEND_API_URL` is now documented as the backend BASE (`http://localhost:8000`); chat proxy routes normalize legacy `/chat` suffixes and log the target URL on 503; `/api/chat`→`{base}/chat`, `/api/chat/stream`→`{base}/chat/stream`. (3) Full suite: **1387 passed / 83 failed** (1472 collected, 2 deselected) — the 83 are exactly the pre-existing baseline files (chat/citation/history/contract/gate-pipeline/grievance-fk/grievance-intent/multilingual/providers/voice route tests, all failing at Clerk-auth 401 without a token); zero failures in any retrieval/orchestrator/recovery/WebRAG/deadline file. Related suites 92/92 pass; ruff clean. Pushed to GitHub (`nek1912/Serp-ai-2026`, branch `main`, in sync).

`2026-10-05` — **FINAL hardening H1+H2+H3/H4 implemented → WebDiscovery FROZEN FOR HACKATHON DEMO. Search Index REJECTED (decision A, investigation closed).** Changes (2 files): `mandate_map.py:37` agriculture subjects += `crop_relief`,`crop_insurance` (H1, data-only) · `query_classifier.py` ≥2-distinct-explicit-states + society-context gate → `mscs`/central (H2) + `mscs`,`crcs`→cooperative keywords (H3) + `pmjjby`,`pmsby`→schemes keywords (H4; `apy` deliberately skipped — substring of "therapy"). Measured: P0 144 + P1 126 + P2/SerpApi/WebRAG 116 pass · 59-case eval 59/59 OK · readiness U-AG-1 top-1=Gujarat GR (`agri.gujarat.gov.in/gr/krp-2025-1145`), U-MS-1 top-1=CRCS (`crcs.gov.in/public/mscs-election`) · security probes 9/9 · multilingual matrix 64 rows exit 0 · full suite 1379 passed/83 failed (same 83-count as pre-existing baseline; zero failures in any jurisdiction/authority/facets/P0/P1/P2/SerpApi/WebDiscovery/classifier file — verified by filtered re-run) · ruff clean. Frozen: `MAX_BRANCHES=8`, provider timeout 5s, `web_rag_timeout_s=30.0`, ThreadPoolExecutor fan-out, RRF, gates, verifier. Search Index: endpoint works with existing key but no full-pipeline rescue demonstrated, ignores `site:`/`OR` operators, wrong-jurisdiction gov noise, ~2× SerpApi cost — do not revisit before hackathon.

`2026-10-04` — **Docs-vs-code truth audit (all WebDiscovery reports, no behavior change except one noted fix):** re-ran everything and corrected all reports to verified current state. Truth now: P0 files 144 pass (136 at P0 close + 8 named audit-added regression tests) · P1 files 126 pass (19+15+8+20+10+20+23+11) · P2 files 56 pass (13+19+24; earlier "57" was a miscount, never true) · combined focused 326 pass · adjacent 247 pass · 59-case eval 59/59 outcomes + 113/113 checks (results committed) · security probes 9/9 · multilingual matrix 64 rows, 12 native activations, 0 crashes · full suite 1379 passed / 83 failed (file-by-file identical to pristine-tree baseline: 2 citation-route + 4 history + 14 chat + 15 refactored + 13 contract + 9 gate-pipeline + 2 grievance-fk + 7 grievance-intent + 15 multilingual + 1 providers + 1 voice) · ruff clean (fixed 6 RUF100 in eval tooling found during audit) · mandate map 41 orgs/60 domains/28 subjects, lexicon 21 concepts, thresholds 0.25/0.30/2 unchanged, verifier 55/85 unchanged, RERANKER conflict still open by design. New findings recorded (F9 generic-grievance referral misdirection → RBI, disposition useful-but-optional; F10 Gujarati-script jurisdiction implication, disposition optional). Only code change: removed `ict` substring keyword that hijacked `district` queries into an unsupported domain (wrong abstentions) + regression test. H1–H4 hardening still not implemented. P2-4+ still 0.

`2026-10-04` — **FINAL readiness audit → verdict B (ONE SMALL HARDENING PASS, then stop; P2-4+ stays unimplemented).** 30 realistic user questions across 15 categories: 28/30 useful-or-honest outcomes; fraud-safe (fake IRDAI desk quarantined/uncited); abstention-honest 4/4 with competent referrals (incl. jurisdiction-recovery path); validity correct wherever discriminating; GU/HI/romanized end-to-end correct; MR/BN/TA native branches verified. Scorecard lows: jurisdiction 29/30, authority/relevance 28/30 (U-AG-1 ladder-top, U-MS-1 RCS-top, U-CO-2 cyber-top). Fixed during audit: `ict`⊂`district` domain hijack (wrong abstains) + regression test. Specified hardening (not done): H1 crop-relief subjects for agriculture, H2 two-explicit-states→MSCS rule, H3/H4 MSCS/PMJJBY keywords iff zero fallout. Do-not-implement list: citation-exclusion policy, intent rework, trust rescoring, referral l10n, OCR, hidden portals, telemetry, agents/crawlers/index/KG/per-result-LLM/expansion. Evidence: `JANSAHAY_WEBDISCOVERY_FINAL_READINESS_REPORT.md`, `backend/eval/final_cases.py`, `backend/eval/final_readiness.py` (+results JSON).

`2026-10-04` — **WebDiscovery P2 phase-1 complete (P2-1/P2-2/P2-3 only, nothing beyond):** terminology expansion (2 scoped rules, branch-query append + overlap bonus, original preserved + recorded) + PMFBY×Gujarat opt-out exception (−0.80 ladder-type demotion, conditional on home evidence, instruments exempt, other states inert) → I-IN-03/T-HI-03/G-AG-01 GR-top-1; state-uncertainty routing (explicit > district-implied > national veto > session > default; MSCS/national exempt; assumed dampening ×0.5 on crop-insurance geo+fit, branches preserved); multilingual data (verified MR/BN/TA terms + scheme/agriculture concepts, state-keyed native:mr/bn/ta branches, TE/KN/ML/PA/OR documented fallback). Tests: 57 new pass; P0 142 + P1 126 intact; combined 325 pass; adjacent 247 pass; eval 59/59 + 113/113; security 9/9; matrix 64 probes (12 native activations); full suite 1317/83 pre-existing (0 regressions); ruff clean. Perf: mean 4.9 mock-searches, branches mean 4.0/max 7, outcomes 57/2. Reports: `JANSAHAY_WEBDISCOVERY_P2_PHASE1_REPORT.md`. P2-4+: 0 implemented.

`2026-10-04` — **WebDiscovery production-readiness audit (measure-first, no P2): verdict READY FOR P2 (narrowly scoped).** Eval: 59 cases/19 strata (`backend/eval/webdiscovery_eval.json` + 46 fixtures + deterministic mocked runner) → 59/59 outcomes, 108/108 checks; security probes 9/9; 11-language matrix 52 probes, 0 crashes; live smoke (SerpAPI live, Tavily down in this env): 4–6 branches, 20 results, lead round fired, 22–26s provider-bound. Audit fixed 6 concrete bugs, all test-pinned: lexicon "gr"-substring instrument misfire; discover annotation masking per-source jurisdiction (gate/recovery vacuous) → publisher-derived + fill-if-absent; identifier prose-capture guard; sanctioned-from/vN/replacing/GU-HI instrument patterns; classifier roman/agri/grievance keyword gaps; society-aware mandate fit + jurisdiction-incompatibility demotion (−0.80, explicit/MSCS only). Baseline A/B on pristine tree: 3/4 headline traps were wrong pre-P0/P1, fixed now. Open weaknesses filed as taxonomy (vocabulary gap F1-high → P2 expansion; assumed-state tension; wrong-forum-citable policy; multilingual data gaps; intent ties; trust margins; Tavily env failure). Full suite 1317 passed/83 pre-existing failed (0 regressions); ruff clean. Reports: `JANSAHAY_WEBDISCOVERY_PRODUCTION_READINESS_AUDIT.md`. P2 roadmap ranked (expansion → uncertainty routing → multilingual data → citation policy → rest deferred); P2: 0 implemented.

`2026-10-04` — **WebDiscovery P1 implemented (8/8, additive, P2: 0):** lead-following (≤3 leads, 1 official-targeted round, lead_only citation bar at 3 enforcement points) · version/mirror clustering (conservative merge, version splits, advisory canonical) · MMR-lite diversification (reorder-only post-rerank, gate multiset unchanged) · bounded recovery (7 evidence states, ≤2 rounds/1 axis, no DOMAIN_MISMATCH retry, `max_recovery_rounds` opt-out) · referral-on-abstention (mandate-map authority/channel, additive `referral` key, contract test 14→15 keys) · impersonation screening (~35 brands + structural rules, quarantine −1.50, 9 legitimate classes clean) · identifier search (GU/Dev→Arabic numerals, section/Act/Rule IDs, 1 shared branch, +0.60/+0.45) · status branch (PIB/Sansad anchors, currency from validity). Fixed en route: per-source state fill-only-if-absent (enrichment masked jurisdiction). Tests: 126 new P1 pass, 264 P0+P1 pass, full suite 1317 passed/83 pre-existing failed (0 regressions, arithmetic-closed); ruff clean. Perf (mocked): 4–12 calls/discovery, wall flat via concurrency, cap 8 (max observed 7). Reports: `JANSAHAY_WEBDISCOVERY_P1_IMPLEMENTATION_REPORT.md`. Limits: Gujarat-only districts, stated-only supersession, no OCR, referral summaries English-templated. Open UNKNOWNs: production reranker state, legacy gate-twin removal.

`2026-10-04` — **WebDiscovery P0 implemented (5/5, surgical, no P1):** jurisdiction resolution (district/society-type/case-time/assumption flags + jurisdiction-first branch; MSCS central-only) · validity-aware freshness (9 stated-only signals in `EvidenceChunk.metadata`, precedence valid>unknown>superseded, `as_of_date` wired chat→orchestrator→web→rescore) · mandate map (41 orgs/59 domains, fit signal + 4 doc roles, `SourceVerifier`/thresholds untouched) · Gujarati/Hindi lexicon branches (19 verified concepts, property-tested) · bounded facets (6-facet template, ≤2 facet branches, cap 8, concurrent, advisory coverage). Frozen intact: provider contracts/fan-out, RRF(60), gates, citations, abstention, static RAG. Tests: 136 new P0 pass, 299 combined pass, full suite 1191 passed/83 pre-existing failed (pristine-tree A/B identical — 0 regressions); ruff check clean. Perf (mocked): ~2–3× provider calls at unchanged wall-clock via concurrency. Reports: `JANSAHAY_WEBDISCOVERY_P0_IMPLEMENTATION_REPORT.md`. Remaining P1: lead-following, clustering, MMR, referral, impersonation filter, identifier search, eval set. Known limits: Gujarat-only districts, no GU/HI month names or numerals, stated-only supersession. Open UNKNOWNs: production reranker state (env vs default), legacy gate-twin removal.

`2026-10-04` — **WebDiscovery engineering audit (no code changed):** wrote `JANSAHAY_WEBDISCOVERY_ENGINEERING_AUDIT.md` (27 sections) mapping research R1–R21 to verified code. Key findings: fan-out/gate/citations solid and frozen; jurisdiction state-only (no district/society-type), freshness = URL-year bonus only (no validity metadata on web chunks), authority = static suffix-gate (not mandate-relative), no GU query branch / facets / lead-following / clustering / referral / impersonation signals. Recommendation: Phase 0 no-code validation (incl. resolve `RERANKER_ENABLED` config-vs-env conflict + dual `evidence_gate` twin ownership) → Phase 1 P0 (jurisdiction+GU branches, validity carriage, mandate map, lead-only citation bar) → Phase 2 P1 → Phase 3 eval. No code, contracts, thresholds, or tests modified in this session.

`2026-10-04` — **Pushed to GitHub (`nek1912/Serp-ai-2026`, branch `main`, 5 commits, in sync):** fresh repo init; hardened root `.gitignore` (`.env*` + `!.env.example`, `venv/`, `.vercel/`, `*.tsbuildinfo`, `.kilo/`, `output/`, `*_output.txt`, benchmark JSONs); secret scan clean (only `***`/`...` placeholders in docs); no file >50MB. Two push workarounds: (1) `.github/workflows/ci.yml` excluded from git (OAuth token lacks `workflow` scope — local copy kept, manage via GitHub web UI, noted in `.gitignore`), (2) slow/flaky network (HTTP 408/aborts on ~39MB pack) → pushed in 5 batches: code → 3× PDF batches → MinerU artifacts. Verify: `git status` clean, `main` == `origin/main` (413 files).

`2026-09-18` — **Final answer presentation and WebRAG provider cleanup:** (1) Enhanced the existing Markdown renderer for answer headings, section rules, blockquotes, tables, links, and mobile-readable spacing without changing answer content, (2) Tavily API keys are attempted concurrently so a slow key cannot block a healthy replacement, (3) live WebRAG discovery returned 20 official results in approximately 15 seconds with the updated environment; Firecrawl remains a non-blocking fallback but returns HTTP 402 due exhausted credits, (4) focused backend checks passed: 42 tests; frontend targeted chat checks: MessageBubble passed, EvidencePanel has 5 pre-existing failures; frontend production build is blocked by existing missing `lenis` dependency/type errors. **Resolved 2026-10-05**: the two dead components importing the absent `lenis` package were deleted, the 5 EvidencePanel failures were stale expectations, and the frontend build now succeeds.

`2026-09-17` — **Chat output and WebRAG cleanup:** (1) Fixed `req.mode` being passed as a Groq model name (`rag_web`), which caused a 404 and made the requested pipeline fall back unnecessarily; pipeline mode is now passed separately, (2) strengthened the existing answer prompt to require the selected-language script, direct answer plus headings/bullets/short paragraphs, and preserved official terms, (3) WebRAG provider failures now log the provider and bounded error instead of being silent, (4) live discovery probe returned 20 official PMFBY results; Firecrawl remains unavailable because its account returned HTTP 402 insufficient credits, (5) focused verification: 94 tests passed, final WebRAG/evidence checks: 32 passed.

`2026-09-17` — **Output formatting cleanup:** Preserved paragraph and markdown separation when Sarvam translates long final answers split across API-sized chunks. The tested `modern-colloquial` Sarvam mode and English grounding boundary remain unchanged. Focused output tests: 59 passed; broader chat/language/translation tests: 60 passed.

`2026-09-17` — **RAG V3 performance and translation boundary fixes:** (1) WebRAG total budget reduced from 90s to configurable 15s with cancellation and awaited cleanup on timeout; static retrieval continues independently, (2) Tavily and Firecrawl default request timeouts bounded to 5s, (3) Gemini reranker timeout configurable at 8s with AFC disabled; Jina fallback timeout configurable at 5s, (4) reranker provenance now records `reranker_used` and `reranker_fallback_reason`, (5) final reranking logs identify Jina fallback correctly, (6) Sarvam translation calls are stage-tagged (`input_query`, `final_answer`, `other`) and the SSE route now enforces the same single final-answer translation boundary as sync chat, (7) citation markers are protected during final translation, (8) timing telemetry added for query translation, static retrieval, WebRAG, generation, grounding, final translation, and total request, (9) WebRAG now uses its discovered-result BM25 ranker instead of the stale 1000-entry static snapshot, preserving the existing ranking call contract, (10) focused regression tests pass: 61 translation/reranker tests and 25 WebRAG/reranker tests; full backend suite: 1055 passed, 28 pre-existing failures, 2 deselected.

`2026-09-17` — **Part 3: Strict Evidence-Grounded Answer Generation (RAG V3):** (1) Strengthened `_SOURCE_PRIORITY_PROMPT` with 8 new rules: evidence is only factual authority, preserve material terms exactly, no synonym substitution for enumerated facts, closed-world numbers/thresholds, no document section merging, explicit conflict handling, missing information stays missing, user-friendly language allowed but factual terms survive, (2) `detect_enumeration_question()` — regex-based detector for list/category/eligibility questions (EN, HI, GU keywords), (3) `answer_grounding.py` — new module with `UnsupportedClaim`, `GroundingResult`, `verify_answer_grounding()` using regex extraction (numbers, dates, entities, conditions) + optional LLM verification layer, (4) Wired grounding check into `RAGOrchestrator` after citation verification (Step 9.5), removes unsupported claims from answer, (5) Enumeration prompt injection — when `detect_enumeration_question()` matches, adds "ENUMERATION MODE" instruction to user prompt, (6) `test_evaluation_grounding.py` — 12 evaluation test cases based on C01/D06/S08 failure patterns, (7) `ANSWER_GROUNDING_LLM_ENABLED` config flag (default False) for optional LLM verification layer, (8) All tests pass: 245/245 Part 3 tests; 5 pre-existing failures (embedding URL mock mismatch in `test_contract.py` and `test_evidence_gate_pipeline.py`); ruff lint clean; mypy not installed.

`2026-09-17` — Full i18n for all pages: (1) Added ~56 new i18n keys to dictionaries.ts covering schemes detail, services listing/detail, and legal listing/detail pages — all 11 languages, (2) Replaced all hardcoded English strings in `schemes/[slug]/page.tsx` (13 strings: Active badge, section headers like What is it, Who can apply, What do you get, How to apply, Key benefits, Document checklist, Ask AI, Have questions, AI help text, Start conversation), (3) Replaced hardcoded strings in `services/page.tsx` (category labels: All, Credit, Storage, Insurance, Agro services, Subsidy, Membership → now use `labelKey` in CATEGORY_META), (4) Replaced hardcoded strings in `services/[slug]/page.tsx` (11 strings: not found, back to services, Quick Facts, Access, Benefits, Source, How to join, What you get, Have questions, AI help, Start conversation), (5) Replaced hardcoded strings in `legal/page.tsx` (category labels: All, Acts, Bye-Laws, Provisions), (6) Replaced hardcoded strings in `legal/[slug]/page.tsx` (12 strings: not found, back to legal, All legal documents, Quick Facts, Type, Key Provisions, provision count, Applicability, Source, Related documents, Have questions, AI help, Start conversation), (7) Added native I18nText translations for 3 previously untranslated services (pm-fb-enrollment, cooperative-training, digital-banking) — all 11 languages for name, summary, description, whoCanUse, howToAccess, source.label, (8) Fixed TS errors: removed duplicate dictionary keys (44 lines), removed impossible `"all"` comparisons in legal page (LegalCategory doesn't include "all").

`2026-09-17` — Language expansion (6→11) + model routing fix: (1) Added 5 new Sarvam-supported languages — Telugu (te), Kannada (kn), Punjabi (pa), Odia (or), Malayalam (ml) — wired existing dictionaries into `LOCALES`, `LanguageSwitcher`, and `dict` export, (2) Updated backend: `ChatRequest.language` Literal expanded to 11 langs, `language_config.json` updated with scripts/stopwords/supported_languages for all 11, `language.py` updated `_SCRIPT_TO_LANG` (9 scripts), `_EXPLICIT_LANG_NAMES` (11 langs), `_EXPLICIT_RE` regex, `normalize_language()` detection for tamil/telugu/kannada/gurmukhi/odia/malayalam scripts, `detect_query_languages()` presence+dominant detection for all 9 Indic scripts, `english_retrieval_query()` now handles all 9 scripts, (3) Added `_THINKING_MESSAGES` and `_STEP_LABELS` for te/kn/pa/or/ml in chat.py, (4) Model routing fix: V1 (static) now runs only StaticRAGService, V2 (web) now runs only WebRAGService, V3 (rag_web) unchanged — both pipelines in parallel; `mode` from `ChatRequest` now passed to `RAGOrchestrator.run()` as `model_override`, orchestrator's `_run_pipelines()` conditionally executes pipelines based on mode.

`2026-09-17` — Brand consistency + full i18n overhaul: (1) Unified brand name to "JanSahay" across all files — fixed "JanSayah" typo in dictionaries.ts (chat.home, chat.user, chat.disclaimer, taglines, footer email), "Sahkarita" in FloatingChatWidget greeting, "eGovAssistant" in grievance draft warnings, (2) Fixed localized tagline translations — GU (સહકારિતા→JanSahay), BN (সহকারিতা→JanSahay), TA (சகாரிதா→JanSahay), (3) i18n'd FloatingChatWidget — greeting, subtitle, open full chat, placeholder, error message all use `t()` with 6-language keys, (4) i18n'd homepage BENTO_CARDS — 6 feature cards (Multilingual, Voice-enabled, Evidence-backed, 6 Languages, Secure & Private, Guided Next Steps) now use `t()` with new `landing.bento1-6title/text` keys in all 6 languages, (5) i18n'd reviews section title — "Trusted by Cooperative Members Across India" now uses `t("landing.reviewsTitle")` with translations, (6) Fixed ChatWindow localStorage keys from `jansayah_` to `jansahay_`, (7) Fixed footer email domain from `jansayah.gov.in` to `jansahay.gov.in`.

`2026-09-15` — Full responsive overhaul: (1) Homepage hero removed hardcoded `ml-36`, added responsive padding/text/CTA/trust badge sizing, (2) Library page added missing `px-*` padding, (3) ArcCarousel rewritten with mobile-first stacked card layout (220px) + desktop 3D carousel (320px), (4) Stepper hidden labels on small screens with smaller circles, (5) Grievance classification replaced table with stacked flex layout for mobile, (6) Grievance Status page added padding + stacked search input/button, (7) Grievance Draft View added responsive padding, (8) FloatingChatWidget responsive width `w-[calc(100vw-2rem)] max-w-[380px]`, (9) All detail pages (schemes, services, legal) updated to `px-4 sm:px-6 md:px-12` pattern, (10) FAQ page responsive padding.

`2026-09-15` — Added thinking process animation: (1) `on_step` callback in `RAGOrchestrator.run()` emits structured step events at each pipeline stage, (2) `_STEP_LABELS` localized labels (6 languages × 6 step IDs) + `_make_step_emitter()` in `chat.py`, (3) New `StepEvent` type + `"step"` SSE event in `api.ts`, (4) `ThinkingProcess` component replaces `ThinkingBubble` — step list with spinner/checkmark, auto-collapse on token arrival, dropdown chevron to re-expand, (5) Wired into `ChatWindow` and `FloatingChatWidget` with `thinkingSteps` state + `step` event handler, (6) 7 new ThinkingProcess tests, 4 updated ChatWindow tests, all passing.

## Current state

System is **feature-complete**. Backend RAG pipeline, 9-stage grievance workflow,
voice I/O, multi-language support (11 languages), and the React/Vite frontend are all
implemented and wired together.

**Selected state:** `gujarat` (`selected_state: "gujarat"` in `backend/app/config.py`)

**LLM config (locked):** Primary=`openai/gpt-oss-120b` (Groq), Fallback=`qwen/qwen3.8-27b` (Groq), Ultimate=Gemini `gemini-2.5-flash`

---

## Component status

`not started / stubbed / in progress / working / broken`

| Component | File(s) | Status | Notes |
|---|---|---|---|
| FastAPI app + `/health`, `/health/providers` | `app/main.py` | working | 6 routers registered (including documents) |
| `/chat` (sync) | `app/routes/chat.py` | working | Language detect → domain classify → RAGOrchestrator or GrievanceWorkflow; clean language boundary for grievance (input translate → English workflow → output translate); multilingual routing with Tier 2 grievance-keyword override + Tier 3 non-English guard; 11-language support (en, hi, gu, mr, bn, ta, te, kn, pa, or, ml); mode-aware routing (static/web/rag_web) |
| `/chat/stream` (SSE) | `app/routes/chat.py` | working | Same pipeline, Server-Sent Events with `thinking/token/metadata/done` events (verified in code — no `step` event is emitted); step events show pipeline progress; same multilingual routing fixes |
| `/voice`, `/voice/transcribe`, `/voice/speak` | `app/routes/voice.py` | working | Full audio→STT→RAG→TTS pipeline |
| `/conversations` | `app/routes/conversations.py` | working | Session history retrieval |
| `/evidence` | `app/routes/evidence.py` | working | Evidence endpoint |
| `/grievance` (route) | `app/routes/grievance.py` | working | Grievance REST endpoint |
| `/documents/pdf/{filename}` | `app/routes/documents.py` | working | Safe PDF serving with path traversal prevention |
| Domain classifier (AnchorStore) | `app/domains.py` | working | Keyword rules + embedding cosine; floor 0.20 |
| Session store | `app/session_store.py` | working | Supabase-backed, keeps last 50 messages; frontend resets on new-chat/load/delete |
| Language detection | `app/language.py` | working | Detects dominant language and language mix; supports 11 languages (en, hi, gu, mr, bn, ta, te, kn, pa, or, ml) with 9 Indic scripts |
| Translation (Sarvam primary, Azure fallback) | `app/providers/sarvam_translator.py`, `app/providers/translator.py` | working | Used in chat.py pre/post RAG |
| RAGOrchestrator | `app/services/rag_orchestrator.py` | working | Mode-aware: V1/V2/V3 pipeline routing; evidence merge, prompt building, LLM generation; includes `_complexity_classifier` for SIMPLE/COMPLEX query routing |
| QueryComplexityClassifier | `app/scenario_reasoning.py` | working | Regex + keyword classifier: SIMPLE vs COMPLEX (procedures, eligibility, comparisons, multi-hop, ambiguous) |
| ScenarioPlanner | `app/scenario_reasoning.py` | working | LLM-based planner: extracts structured requirements + missing user facts; JSON fallback on LLM failure |
| EvidenceMapBuilder | `app/scenario_reasoning.py` | working | Merges retrieval results into unified evidence map with dedup, section coverage, multi-document tracking |
| DerivedConclusionEngine | `app/scenario_reasoning.py` | working | Generates conclusions from evidence-supported requirements only |
| Answer grounding | `app/answer_grounding.py` | working | Regex claim extraction, condition extraction, enumeration detection; verifies facts against evidence |
| StaticRAGService | `app/services/static_rag.py` | working | Supabase pgvector hybrid retrieval (dense + lexical RRF) → EvidenceChunks |
| WebRAGService | `app/services/web_rag.py` | working | 10-step web RAG: Tavily/SerpApi-Google/Firecrawl → BM25 → Gemini pre-rank → RRF → Gemini final-rank → source verify → EvidenceChunks; Gemini deadline clamped ≥10s (API minimum) |
| EvidenceController + prompt builder | `app/evidence_controller.py` | working | Merges chunks, builds curated source-priority prompt |
| Evidence gate | `app/evidence_gate.py` | working | Threshold: `TOP1_THRESHOLD=0.25`, `SECONDARY_THRESHOLD=0.30`, `MIN_CHUNKS_ABOVE_SECONDARY=2` |
| Citation verifier | `app/citation_verifier.py` | working | Set-membership check — every `[chunk:id]` must map to a retrieved chunk; full `web_*` IDs kept whole (truncated 8-char web prefixes stay ambiguous → invalid); evidence URLs allowlisted (naming the official portal is not fabrication); format variants normalized pre-verification |
| Confidence calculation | `app/services/rag_orchestrator.py` | working | Band-based; dual-source gets +0.10 boost |
| GrievanceWorkflow (9-stage state machine) | `app/grievance/workflow.py` | working | INTAKE → CLASSIFICATION → ENTITY_EXTRACTION → MISSING_FIELDS → FOLLOWUP → DRAFT_READY → SUBMISSION_GUIDE → STATUS_LOOKUP → COMPLETE; English-only source of truth; fresh-state defense for new complaints after completed grievance |
| Grievance classifier | `app/grievance/classifier.py` | working | |
| Grievance draft builder | `app/grievance/draft_builder.py` | working | English-only; canonical dict exposes `description.original` for user's pre-translation text |
| Grievance entity extractor | `app/grievance/entity_extractor.py` | working | |
| Grievance field detector | `app/grievance/field_detector.py` | working | `FIELD_LABELS` dict (150+ entries), `get_field_labels()` for i18n field names; prompts translated via `translate_field_prompt()` using `FIELD_PROMPTS` map |
| Grievance semantic extractor | `app/grievance/semantic_extractor.py` | working | |
| Grievance submission guide | `app/grievance/submission_guide.py` | working | Portal lookup; output translated at boundary |
| Grievance status lookup | `app/grievance/status_lookup.py` | working | |
| Grievance state persistence | `app/grievance/workflow.py` | working | Supabase `grievance_states` table, upsert on `conversation_id` |
| Grievance localization layer | `app/routes/chat.py`, `app/routes/grievance.py`, `app/grievance/translations.py` | working | Backend translates: field prompts (FIELD_PROMPTS map), submission steps, followup prefixes, workflow prefixes, field labels, draft_summary, canonical dict; user values preserved verbatim; frontend translates field card labels via i18n dictionary |
| Routing hierarchy | `app/routes/chat.py`, `app/grievance/workflow.py` | working | Tier 1: domain/intent → grievance; Tier 2: guidance intent → RAG, grievance-keyword override; Tier 3: non-English guard; informational regex |
| Grievance UI (frontend) | `frontend/src/components/chat/GrievanceFlow.tsx` | working | Orchestrates stage panels; `GrievanceClassificationPanel`, `GrievanceFieldPanel`, `GrievanceCard` (renders i18n-translated field labels) |
| Session isolation | `frontend/src/components/ChatWindow.tsx` | working | `useRef` + `resetSessionId()` prevents state leakage across "New Chat" |
| VoiceService (STT/TTS fallback chain) | `app/services/voice_service.py` | working | STT: Sarvam→Azure; TTS: Sarvam only (Azure bad for Indic langs) |
| Sarvam STT/TTS providers | `app/providers/sarvam_voice.py` | working | Primary voice provider |
| Azure STT fallback | `app/providers/azure_voice.py` | working | Fallback STT only |
| Embeddings (Jina primary, Gemini fallback) | `app/providers/embeddings.py` | working | Jina v3 768d, task-typed (`retrieval.query` / `retrieval.passage`) |
| Jina reranker | `app/providers/reranker.py` | working | Wired in StaticRAGService but **disabled** (`RERANKER_ENABLED=false`) |
| Gemini LLM provider (fallback) | `app/providers/gemini_llm.py` | working | `_classify_error()` for structured error classification; tiered model fallback |
| Groq LLM provider (primary) | `app/providers/groq_llm.py` | working | Primary=`openai/gpt-oss-120b`, Fallback=`qwen/qwen3.8-27b`; key rotation + `_classify_error()` |
| Sarvam chat provider | `app/providers/sarvam_chat.py` | working | |
| Web discovery (Tavily / SerpApi Google / Firecrawl) | `app/web_rag/service.py` | working | `WebDiscoveryService`: bounded branches (MAX_BRANCHES=8, concurrent) × concurrent provider fan-out; SerpApi Search Index evaluated 2026-10-05 and rejected |
| Query classifier (web RAG) | `app/web_rag/query_classifier.py` | working | Domain, jurisdiction, state, society-type classification for web queries; H1/H2/H3/H4 hardening implemented 2026-10-05 |
| Source verifier | `app/security/source_verifier.py` | working | Trust-score based filtering in web RAG |
| Frontend SPA (**not** a PWA) | `frontend/` | working | React 19 + Vite 8 + React Router 7 + Tailwind v4 + GSAP; fully responsive (320px–desktop). **No web app manifest and no service worker exist** — the PWA label in earlier entries of this file was never true. Migrated off Next.js on 2026-10-05; `frontend/` is retained as a fallback |
| Frontend API access | `frontend/src/lib/backend.ts` | working | Browser calls FastAPI directly with Clerk's session token. `backend.ts` owns the base URL, the legacy `/api/*` → FastAPI path mapping, and the bearer header. No proxy server, no second port |
| Frontend config loading | `backend/app/config.py` | working | Reads `backend/.env` by absolute path (only backend source of truth). A repo-root `.env`, if present, is ignored with a RuntimeWarning so two files can never silently disagree |
| Frontend pages | `frontend/src/pages/` | working | `/` (home), `/chat`, `/grievance`, `/schemes`, `/services`, `/library`, `/faq`, `/legal` — all with responsive padding and mobile-first layouts; homepage bento cards + reviews section fully i18n'd |
| Frontend i18n (11 languages) | `frontend/src/lib/i18n/` | working | EN, HI, GU, MR, BN, TA, TE, KN, PA, OR, ML; includes field label translations (45 keys per locale) for grievance card rendering; bento card titles/texts (6 cards × 2 keys), reviews title, widget strings (greeting/subtitle/openFull/placeholder/error) |
| ChatWindow (streaming SSE) | `frontend/src/components/ChatWindow.tsx` | working | Handles `thinking/token/metadata/done` SSE events (backend emits no `step`/`error` events), voice recording, citation display; localStorage keys use `jansahay_` prefix |
| Thinking Process UI | `frontend/src/components/chat/ThinkingProcess.tsx` | present but unwired | File exists; nothing consumes it — backend emits no `step` events and ChatWindow has no step wiring |
| Evidence Panel | `frontend/src/components/chat/MessageBubble.tsx` | working | Unified `EvidencePanel` + `EvidenceCard` components; `data-evidence="true"` attribute; citation tags with `aria-expanded`/`aria-label`; keyboard-focusable; scroll-into-view on expand |
| Document ingestion pipeline | `backend/seed_parser.py`, `backend/ingest_seed.py` | working | Parses MinerU `content_list_v2.json` → JSONL → embeds → Supabase |
| Database schema | `backend/schema.sql` | working | `documents`, `chunks` (vector 768d, HNSW), `sessions`, `grievance_states` |

---

## Provider status

| Provider | Status | Role |
|---|---|---|
| Groq | configured | Primary LLM (key rotation supported) |
| Gemini | configured | Fallback LLM + Gemini reranker in WebRAGService + grievance model |
| Jina | configured | Primary embeddings (jina-embeddings-v3, 768d) |
| Supabase | configured | Postgres + pgvector (HNSW cosine), sessions, grievance_states |
| Sarvam AI | configured | Primary STT, TTS, translation (key rotation supported) |
| Tavily | configured | Primary web search (`TAVILY_API_KEY_1/2`, 5s timeout, 2-key concurrent race) |
| SerpApi Google | configured | Live web-search provider (`SERPAPI_API_KEY_1/2`, `engine=google`, 5s timeout, sequential key fallback); Search Index engine evaluated and rejected 2026-10-05 |
| Firecrawl | configured | Web crawl / scrape fallback |
| Azure Cognitive Services | configured | Fallback STT only (TTS deliberately excluded — bad Indic output) |
| Bhashini / ULCA | stubbed | `bhashini_stub.py` present, not wired |
| Render | configured | Backend hosting (`render.yaml`) |

---

## Known issues / caveats

- **Reranker disabled**: `RERANKER_ENABLED=false` in config. When enabled, Recall@1 drops 0.85→0.50. Keep off.
- **Agriculture has no ingested corpus chunks** (corpus table below has no agriculture domain): static retrieval maps `agriculture` → `pmfby` corpus (`static_rag.py:34`); the web path serves `agriculture` fully (supported domain + state-competent + mandate subjects incl. `crop_relief`/`crop_insurance` since 2026-10-05). It does NOT route to `out_of_scope`.
- **Gold eval set is retriever-anchored**: Recall metrics are optimistic (measures if retriever surfaces its own best-matching chunk, not true answer span). Manual curation needed for production eval.
- **Supabase free-tier pausing**: May pause after inactivity. Reactivate before demos.
- **Dead Groq model**: `llama-3.3-70b-versatile` is DEAD on Groq (HTTP 404). Use `openai/gpt-oss-120b` (primary) and `qwen/qwen3.8-27b` (fallback) only.
- **MoC_Young_Professionals_YPs.pdf**: Scanned/image-based PDF processed via EasyOCR + pymupdf. OCR text is lower quality than MinerU extraction. 213 chunks embedded (611 raw from OCR).
- **Pre-existing test failures (backend, re-verified 2026-10-06)**: full suite 1387 passed / 83 failed (1472 collected, 2 deselected) — the 83 are the exact pre-existing baseline files (chat/citation/history/contract/gate-pipeline/grievance-fk/grievance-intent/multilingual/providers/voice route tests, failing at Clerk-auth 401 without a token), with zero failures in any jurisdiction/authority/facets/P0/P1/P2/SerpApi/WebDiscovery/classifier/orchestrator/recovery/deadline file. Unrelated areas only.
- **Frontend tests: fully green.** The 12 failures recorded here previously were measured on 2026-10-05 (not the 7 this file used to claim) and are all resolved: 3 were real source bugs (speech cancellation leaked a pending promise and an `Audio` element; `application_id` rendered as "Application Id"), 8 were stale test expectations, and 1 asserted a total i18n coverage that does not exist. `frontend` runs 84 tests across 18 files, all passing.
- **Fixed**: static RAG returned zero chunks — the database has two overloaded `match_chunks` signatures and PostgREST raised PGRST203 on the 4-arg call, so every answer abstained. Both call sites now name all six parameters.
- **PDF endpoint**: Regex allows `A-Za-z0-9_\-\.(), ` for filenames. Path traversal blocked. Non-PDF extensions rejected.
- **`chunks.source_file` column**: Does NOT exist in live Supabase DB. `source_file` is stored in `chunks.metadata` JSONB instead.

---

## Corpus

All ingested from `corpus/seeds/json_files/*_content_list_v2.json`
via `backend/seed_parser.py` → `backend/ingest_seed.py`. Embeddings: Jina v3 768d.

| Domain | Chunks embedded | Source |
|---|---|---|
| pacs_governance | 1294 | Model Byelaws (337) + HR Policy V21 (601) + MoC YPs (213) + CSM Scheme (43) |
| pacs_computerization | 214 | Revised Scheme guidelines (192) + Corrigendum (22) |
| pmfby | 1266 | operational_guidelines_pmfby |
| financial_inclusion | 2004 | NSFI_2025_30 (371) + RBI FAME (579) + RBI BE(A)WARE (429) + IRDAI Insurance (725) |

**Total: 11 documents, 4778 embedded chunks, 768d Jina v3**

### PDF provenance chain

```
PDF (corpus/seeds/*.pdf)
  -> pypdf extraction -> corpus/seeds/chunks_jsonl/*.jsonl (source_file per chunk)
    -> ingest_seed.py (DOC_META -> Supabase documents + chunks.metadata)
      -> StaticRAGService -> EvidenceChunk.metadata["source_file"]
        -> _build_citations() -> citation["source_file"]
          -> Frontend EvidenceCard -> /api/documents/pdf/{source_file}#page={page}
```

---

## Flagship demos

1. **Hindi PMFBY voice query** — Audio → Sarvam STT → RAGOrchestrator → Sarvam TTS audio response
2. **Cooperative/PACS state-filtered question** — `state="gujarat"` filtered in `static_rag.py` pgvector queries
3. **Grievance intake + status lookup** — Multi-turn intake → entity extraction → prototype reference (`DEMO-PACS-xxxxx`) → status lookup guidance; supports 6 languages via clean input/output translation boundary

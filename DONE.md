# DONE — Completed Work Log

## 2026-03-27

### [data] Vehicle Realization Plan v2 — table-driven decomposition
- `stage_transition_labor_map`: added `category` column + 13 new rows (powertrain, interior, electrical, chassis, assembly) — now 28 rows across 6 categories
- `get_comp_tiers(year, make, model_root)`: new reusable SQL function returning 4 market tiers with counts/avg/min/max from sale data
- `persist_realization_plan()`: rewritten as v2 orchestrator — reads enriched fields (engine_type, known_flaws, condition_rating, description_discoveries, vehicle_observations) before falling back to regex; steps now sourced from `stage_transition_labor_map` with `map_id` traceability; `data_sources` field tracks which inputs were available
- Wired into 3 edge functions: `enrich-listing-content`, `discover-description-data`, `process-cl-queue` — plan recomputes after each extraction pass
- Verified: C10 (project) → 7 steps/$17.5K-$34.2K; Packard (driver) → 3 steps/$2.6K-$8.7K; Camaro (show) → 3 optional steps

### [research] Auction Price Formation Theory — CBT empirically validated
- Updated paper status from "Theoretical" to "Empirically validated — CBT = 4 serious bidders"
- Added Section 1.4: Serious Bidder definition (max bid >= 70% of auction high, mode of 4 per BaT auction)
- Test 1 (bid count): PASS with cohort-controlled results (7 buckets, 36K vehicles)
- Test 3 Original (unique bidders): INCONCLUSIVE — no threshold visible, game-players muddied signal
- Test 3 Revised (serious bidders): PASS — threshold at 4, median deviation 0.0% from 4 through 10
- Test 4 Revised (variance): PASS — stddev drops 0.941→0.739 from 2→4 serious bidders
- Key finding: 2 serious bidders = highest overpay risk (mean +27.7%, "emotional duopoly")
- Updated Research Frontier Q1 as answered, For the Next Agent section with remaining tests (2, 5, 6)

### [frontend] Vehicle Profile 6-Phase Renovation — committed f90ac7d7a
- Phase 1: AppHeader/VehicleTabBar z-index and sticky alignment fixes
- Phase 2: VehicleSubHeader removed unused image count badge
- Phase 3: WorkspaceContent — BuildStatusPanel + OwnerIdentityCard integration, empty state guards
- Phase 4: VehiclePricingValueCard/ROISummaryCard null-safe rendering
- Phase 5: NukeEstimatePanel empty data guard
- Phase 6: VehicleReferenceLibrary comments-first reorder
- 13 files committed (10 modified + 3 new: BuildStatusPanel, OwnerIdentityCard, useBuildStatus hook)
- tsc clean, vite build clean (12s)

### [frontend] Vehicle Profile: Owner Throne + Build Status Panel
- Created `useBuildStatus.ts` hook — parallel fetch from `work_order_receipt_unified` + `deal_jackets` with contact join
- Created `OwnerIdentityCard.tsx` — avatar + name + OWNER badge + sale price/date/deposit grid. Address gated to owner/contributor.
- Created `BuildStatusPanel.tsx` — charged/paid/balance summary, work order rows with expand-on-click lazy loading parts/labor/payments. Rate source gated to owner view.
- Modified `WorkspaceContent.tsx` — 2 lazy imports, hook call, 2 conditional render insertions (after dossier + after build timeline)
- Self-guarding: both components return null when no data, no empty shells
- TypeScript compiles clean, zero errors

### [design] Visual Audit → Wireframe Prototyping → Design Ontology
- Full forensic audit of nuke.ag: every UI element traced to its design spec prompt, identified gaps between spec and reality
- Identified novel data advantages: 7 ontological dimensions no other platform surfaces (palimpsest lifecycle, evidence chains, epistemological decay, spatial condition, actor networks, market consensus, coverage depth)
- Built 6 wireframe prototypes at `wireframes/` (A-F): Bloomberg data-forward, signal strip, overlay badges, sortable dashboard, badge portals, final synthesis
- Simulated 7 design critics (Tufte, Rams, Ive, Ishii, Eames, Norman, Chimero) and synthesized feedback
- Discovered badge portal interaction pattern: every data point is a clickable door into unique data shapes
- Discovered image ownership ontology gap: 42K photos mis-assigned by bulk import, `vehicle_id` conflates storage/attribution/subject/provenance
- Found album_sync_map: 65 albums, 11,316 photos, already mapped to vehicles, zero synced
- Architecture docs: `docs/architecture/IMAGE_OWNERSHIP_ONTOLOGY.md` (4-relationship model), `docs/architecture/IMAGE_REVIEW_PASSES.md` (multi-pass correction framework)
- Final wireframe (F) implements tiered progressive disclosure: image overlay → Tier 1 signal strip → Tier 2 deep data → leaf evidence nodes
- Key design decisions: no data redundancy across layers, every leaf terminates at evidence (photo/doc/part/listing/actor), academic ontology renamed for consumers

### [fb-saved] Facebook Saved Items Auto-Extraction Pipeline
- Built batch mode on `extract-facebook-marketplace` (mode: "batch") for saved items ingestion
- Created `scripts/fb-saved-sync.sh` — two-phase AppleScript+curl sync (DOM extract → POST)
- Created LaunchAgent `com.nuke.fb-saved-sync.plist` — fires every 30 min automatically
- Fixed chicken-and-egg bug: refine no longer requires vehicle_id (saved items arrive unlinked)
- Fixed import image gate: saved items bypass image requirement (user-curated = real vehicles)
- Fixed `isBlockedVehicleType` undefined error in import-fb-marketplace
- Ran full enrichment on 75 saved vehicles via Playwright from residential IP
- Results: 96% descriptions, 35% transmission, 31% mileage, 99% price
- Documented in Engineering Manual Ch.8 (Scraping Sources → Saved Items Pipeline)
- Deployed: extract-facebook-marketplace, refine-fb-listing, import-fb-marketplace

### [realization] Vehicle Realization Plan — persist_realization_plan() + Strategy Doc
- Created `persist_realization_plan(vehicle_id)` SQL function: parses vehicle description for physical state (engine, trans, body, paint, interior, title, matching numbers), derives deterministic resolution steps with cost/time ranges, pulls comp tiers (project/driver/restomod/show) from our data, stores as JSONB on `vehicles.realization_plan`
- Applied migration `vehicle_realization_plan`: `labor_estimates` table (designed months ago, never deployed), `realization_plan` JSONB column on `vehicles`
- Test case: 1971 C10 Fleetside Short Bed ($10K, Las Vegas CL) — ingested as vehicle `507198f2`, 17 images, realization plan computed: 7 steps, $10.3-36.5K build, 1,412 comps across 4 tiers
- Strategy doc: `docs/products/DEAL_FLOW_ACQUISITION_ENGINE.md` — full inventory of what exists vs schema-only vs missing for deal detection, 7-dimension scoring model, phased execution plan
- Key finding: CL queue processor stalled since Feb 25 (124 items stuck in `processing`). 707 CL feeds active but queue not draining.
- Key finding: `vehicle_watchlist`, `watchlist_matches`, `auto_buy_executions`, `price_monitoring`, `marketplace_deal_alerts`, `notification_channels`, `user_subscriptions` — all have migrations written but tables never created in production
- Concept: realization plan is NOT a product — it's a computed field derived from vehicle state, same as ARS. Every vehicle gets one on ingest. The steps are physics, not features.

### [extraction] Mecum Re-Extraction Phase 1 — Snapshot Pipeline Fix + Queue Population
- **Bug fixed:** `repopulate_snapshot_queue()` had `s.html IS NOT NULL` condition that blocked ALL platforms — 100% of snapshots (440K+) use `html_storage_path` not inline html. Changed to `(s.html IS NOT NULL OR s.html_storage_path IS NOT NULL)`.
- **URL normalization added:** repopulate function now handles www vs non-www and trailing slash mismatches. Previously only exact URL match worked.
- **Queue populated:** 30K+ Mecum vehicles queued for extraction (up from 18K). Total queue: 77K items.
- **Cron tuned:** `mecum-snapshot-parser` batch_size 50 -> 100. Disabled redundant `enrich-mecum-snapshots` offset-based cron.
- **Drain rate:** ~3.6K items/hour (cron + manual batches). ~29K pending, ETA ~8 hours.
- **Coverage lift (so far):** Engine 49.3% -> 61.5% (+12.2pp). Transmission, color, drivetrain all rising. Projected final: price +3.6pp, desc +3.8pp, mileage +6.7pp.
- **Key discovery:** 78K "Mecum" vehicles are actually ConceptCarz stubs (conceptcarz:// URLs) with 0.7% VIN, 2.7% price. These drag down overall percentages but cannot be improved via snapshot extraction.

### [user-simulation] User Stylometric Analyzer + Persona Simulation Methodology
- **Layer 0 Instrument:** `scripts/user-stylometric-analyzer.mjs` — pure-math stylometric fingerprinting (zero API cost). Computes sentence length distribution, Yule's K vocabulary richness, function word profiles (Mosteller & Wallace), punctuation signatures, epistemic stance (Hyland hedge/boost), self/other reference rates, opening patterns.
- **Stratified Sampler:** Samples by make AND time period to capture expertise phase transitions. Addresses the "SAE vs metric diorama" problem — automotive experts switch domains.
- **Era Detection:** Identifies palimpsest layers of expertise (e.g., 1600veloce: BMW → Chevy → Porsche → BMW → Porsche). Core finding: **style is identity, topic is era**.
- **Empirical Results:** 5 power users fingerprinted with clearly discriminative signatures. DENWERKS: 0.64 exclamation/sent. VivaLasVegas: 30.8 self-reference/1K. 911r: hedge/boost 0.87.
- **Methodology Paper:** `docs/library/intellectual/papers/user-simulation-methodology.md` — full academic methodology grounding (Pennebaker, Yule, Hyland, Park, Schwartz, Mosteller-Wallace, Hullman, DPRF, PersonaCite, Santa Fe ASM). 10 sections, 30+ citations.
- **Batch Run:** Top 1000 users processing, profiles saving to `bat_user_profiles.metadata.stylometric_profile`.
- **Research Database:** Existing infrastructure mapped: `comment_persona_signals` (2,787 rows), `author_personas` (~30 rows), `personaPrompt.ts` (working persona→bot conversion). Identified gaps: scoring fields all zeros, Layer 3 extraction only 0.02% coverage.

### [question-taxonomy] "What Do Buyers Want To Know?" Pipeline — All 4 Phases
- **Phase 1:** Discovery script (`scripts/question-taxonomy-discovery.mjs`) — stratified sampling across 20 price/era cells, Gemini Flash taxonomy discovery, Sonnet consolidation, TF-IDF regex extraction. 6 npm scripts registered.
- **Phase 2:** Migrations — 5 new columns on `auction_comments` (question_categories, question_primary_l1/l2, question_classified_at, question_classify_method), `question_taxonomy` reference table, `question_profile` column on `comment_discoveries`. Partial indexes on l1/l2.
- **Phase 3:** `question_classify` mode added to `analyze-comments-fast` (regex, $0). `question_classify_llm` mode added to `batch-comment-discovery` (Gemini Flash fallback, $0). Both self-chaining, batched.
- **Phase 4:** `mv_question_intelligence` materialized view, `refresh_question_intelligence()` function, `question_gap_analysis()` RPC. Grants to anon/authenticated.
- **Pipeline sequence:** `npm run discover:questions` → taxonomy populates → `question_classify` regex pass → `question_classify_llm` LLM fallback → `refresh_question_intelligence()` → `question_gap_analysis()` reveals buyer intent distribution.
- **Cost model:** ~$0.14 total (1 Sonnet consolidation call). Everything else is Gemini Flash (free) or regex ($0).

### [work-order-intelligence] Environment Hardening — 7 Phases Complete
- **Phase 1:** Schema reconciliation migration — codified work_order_payments, labor_operations, user_labor_rates (new), work_contracts (new). All IF NOT EXISTS. Data preserved (4 payments, 64 labor ops, 71 parts, 19 labor).
- **Phase 2:** Seed data migration — 51 original + 7 new exhaust/brake labor operations, ON CONFLICT DO NOTHING.
- **Phase 3:** `work_order_receipt_unified` view + `work_order_balance()` function. Bridges dual system (timeline_events + work_orders).
- **Phase 4:** `resolve_work_order_status(p_query)` RPC — THE PRODUCT. One call, full answer. Fuzzy resolution, returns vehicle/contact/work orders/parts/labor/payments/balance as JSONB.
- **Phase 5:** Script hardening — shared `lib/env.mjs` (no hardcoded paths), `package.json` for nuke-context, all 5 scripts refactored. `resolve.mjs` now calls RPC as primary path with client-side fallback + iMessage enrichment. Removed hardcoded K2500 vehicle ID from ingest-thread.mjs.
- **Phase 6:** Registered `wo:resolve`, `wo:balance`, `wo:ingest-zelle`, `wo:ingest-receipts`, `wo:ingest-thread` in package.json. Added Work Order Intelligence section to TOOLS.md. 6 pipeline_registry rows.
- **Phase 7:** Library documentation at `docs/library/technical/work-order-intelligence.md`.

## 2026-03-26

### [work-order-intelligence] 5-Component Work Order Intelligence System
Built wiring from data sources to defensible work order receipts:
- **ingest-zelle.mjs**: Reads AFCU SMS from chat.db, found 4 Granholm Zelles ($4,416.73). Created `work_order_payments` table.
- **ingest-receipts.mjs**: Extracted 15 itemized parts from Amazon + Summit via Gmail MCP ($1,074.95 total).
- **balance.mjs**: Full cited receipt. 3 WOs: Parts $1,826 + Labor $3,805 - Payments $4,417 = $1,214 due.
- **ingest-thread.mjs**: Decoded 456 iMessages, detected 15 scope changes, 2 price agreements, 19 status updates. 44 events → vehicle_observations.
- **Labor engine**: Seeded 7 labor_operations, updated 11 labor rows with book times + cited rates.

### [buyer-intelligence] Phase 1: BaT User Behavioral Segmentation
- Created `mv_buyer_profiles` materialized view: **343,661 profiles** segmented from 517K BaT user profiles + 108K vehicle purchase records + 130K sale records
- 8 behavioral segments: WHALE (128), DEALER (1,161), COLLECTOR (1,576), FLIPPER (275), ENTHUSIAST (34,589), BIDDER (57,029), CASUAL (243,992), INACTIVE (4,911)
- $4.4B total tracked transaction volume across all segments
- Whale segment: 128 users, $367M total spend, avg $99K/vehicle, 3,697 vehicles purchased
- Dealer segment: 1,161 users, $2.2B total earned, 40,732 vehicles sold
- Created SQL functions: `classify_buyer_segment()`, `refresh_buyer_profiles()`, `buyer_intelligence_summary()`, `get_buyer_profile(username)`
- Indexes: unique on username, segment, total_spent DESC, vehicles_purchased DESC
- Known issue: ~6K junk usernames from bat_buyer parsing (common English words). Clean buyer count: 101,795
- Data sources: `bat_user_profiles` (pre-aggregated comments/bids), `vehicles.bat_buyer/bat_seller` (purchase/sale records)
- Intermediate tables preserved for MV refresh: `_tmp_buyer_makes_agg`, `_tmp_purchase_stats`, `_tmp_sale_stats`

### [library] Applied Ontology Research Paper Series (5 papers)
- Extended trilogy to full 5-paper series:
  - `from-protege-to-production.md` — Comparative analysis: 5 structural failures of OWL/RDF/Protege for physical asset domains (T-Box/A-Box imbalance, Open World Assumption, atemporal assumption, single-authority assumption, schema-data separation). Full OWL→PostgreSQL equivalence table. Honest "what we lost" section. Decision framework for when to use what.
  - `ontological-lexicon.md` — 50+ term lexicon organized across 8 ontological layers (identity, observation, epistemology, spatial, lifecycle, condition, actor, resolution, meta). Each term: formal origin, platform definition, database implementation, operational example. Quick reference appendix with row counts.

### [library] Applied Ontology Research Paper Trilogy (earlier today)
- Created 3 interconnected papers in `docs/library/intellectual/papers/`:
  - `applied-ontology-vehicle-domain.md` — Framework paper positioning Nuke within formal ontology research. Cites Gruber, Guarino, CIDOC-CRM, PROV-O, DOLCE, BFO, Goldman, Shapin, Deleuze. Covers: immutable identity ontology, epistemological trust layer, schema-as-prompt, actor layer, rhizomatic connectivity, ontological pluralism.
  - `applied-ontology-evidence-map.md` — Evidence map tracing every theoretical claim to exact tables, functions, row counts, code paths. 3.3M observations, 158 sources, 14 half-life tiers, 63 component tables, 150+ views.
  - `novel-ontological-contributions.md` — Seven novel contributions ahead of the formal literature: spatial condition ontology, palimpsest lifecycle model, recursive epistemological decay, disagreement-as-data, executable domain axioms, image fact fabric, component-level total resolution. Includes open research agenda.
- Content positions platform as active participant in applied ontology research

## 2026-03-25

### [data-quality] Enrichment Quality Metrics RPC — enrichment_quality_report()
- Created `enrichment_quality_report()` SQL RPC function returning jsonb with 8 sections: by_source (35 sources), by_extractor (16 extractors), observation_depth, evidence_by_field (16 fields), evidence_by_source_type (30 types), observations_by_method (9 methods), summary, metadata
- Granted to anon + authenticated, callable via `POST /rest/v1/rpc/enrichment_quality_report`
- Key baseline findings: 387K vehicles, 64.1% avg completeness across 10 key fields
- Best sources: Cars & Bids (84.3%), Mecum (83.2%), BaT (75.6%)
- Worst sources needing Sonar enrichment: KSL (1.3%), Facebook Marketplace (10.0%), ConceptCarz (10.1%)
- Best extractor: extract-bat-core:3.0.0 (91.3%), worst: extract-vehicle-data-ai:1.1 (12.6%)
- Sonar/research enrichment will appear in evidence_by_source_type + observations_by_method once pipeline runs
- Optimized for anon 15s timeout: uses pg_class reltuples for big-table counts, avoids count(DISTINCT) on 3M+ row tables
- Marked agent_task 29814fe7 as completed

### [revenue] Fix 3 deal-flow tasks — exchange tables, invoice payments, Stripe Connect
- **Exchange trade flow (P80)**: `market_orders` and `market_trades` tables were dropped by `drop-empty-tables-cascade.sql`. Recreated with full schema, RLS policies, indexes, and service_role grants. The `match_order_book()`, `cancel_market_order()`, `execute_trade()` RPCs and Portfolio.tsx now have their backing tables. 6 vehicle_offerings exist in `trading` status, 6 share_holdings, 4 market_funds, 1 user_cash_balance.
- **Stripe invoice payment (P75)**: The `stripe-webhook` handler called `mark_invoice_paid(p_payment_token)` but the RPC didn't exist. Created it with idempotent paid marking. Added `payment_token` column to `generated_invoices`. 7 invoices exist (all unpaid). **Remaining blocker**: No frontend "Pay Invoice" button that creates a Stripe Checkout session with `purchase_type: 'invoice_payment'` metadata. The webhook handler is now ready to receive these.
- **Stripe Connect onboarding (P60)**: Added `onboarding_complete`, `payments_enabled`, `requirements_status`, `capabilities`, `updated_at` columns to `stripe_connect_accounts`. Updated webhook to persist V2 thin event status changes. Updated `stripe-connect-account` status action to write-through to DB. Frontend now loads account from DB (not just localStorage). 1 test account exists (`acct_1SKfhxAWmE1NEb2Y`, NULL user_id).
- All Stripe secrets confirmed set: `STRIPE_SECRET_KEY`, `STRIPE_WEBHOOK_SECRET`, `STRIPE_PUBLISHABLE_KEY`, etc.
- Deployed: `stripe-webhook`, `stripe-connect-account`

### [data] Dead source revival — Mecum, Barrett-Jackson, RM Sotheby's, Gooding back online
- **Mecum**: Discovered Algolia search index (App: U6CFCQ7V52, 303K lots). Created `scripts/mecum-algolia-discovery.mjs`. Queued 18,516 new lots from 10 recent auctions (Kissimmee 2026, Indy 2025, Glendale 2026, etc). Created `mecum-batch-from-queue` cron (every 5 min).
- **Barrett-Jackson**: Discovered public Strapi API at `barrett-jackson.com/api/docket` (63,832 lots). Created `scripts/bj-api-discovery.mjs`. Queued 10K+ lots. Full 63K discovery running in background. Created `bj-batch-from-queue` cron (every 5 min).
- **RM Sotheby's**: Processed 14 auctions (PA26, AZ26, CC26, MI26, S0226, and 2024-2025 auctions). Created 56 new vehicles. Existing `rmsothebys-discovery` cron continues.
- **Broad Arrow**: Confirmed merged into RM Sotheby's. broadarrowauctions.com returns 403. Their lots now served via RM.
- **Collecting Cars**: Discovery working, 198 active listings all already known. Cron active.
- **Gooding**: Sitemap discovery found 9,278 lots. Batch extraction crons active.
- **Hagerty**: Re-enabled listing_feed. Extractor works. Needs GraphQL discovery.
- **Hemmings**: Still blocked by Cloudflare 403. Needs Firecrawl.

### [data] Niche collector car site onboarding — 20 sources registered, ~98K URLs queued
- **5 new RSS feeds registered and flowing** (poll-listing-feeds cron, every 15min):
  - barnfinds.com (17 items, vehicle titles auto-parsed to Y/M/M)
  - silodrome.com (10 items)
  - thedrive.com (18 items)
  - hagerty.com/media (100 items)
  - hiconsumption.com (10 items)
- **3 sitemap-based bulk ingests completed**:
  - Classic Driver: 51,377 car listing URLs across 27 sitemap pages → 54,725 queued (48K still ingesting in background)
  - Car and Classic: 401 auction listings from sitemap → all queued
  - ER Classics: 1,785 car listings from sitemap → all queued
  - The Market by Bonhams: 5,511 auction listings from sitemap → all queued
- **10 new observation_sources registered**: barnfinds, thedrive, hagerty-media, petrolicious, hiconsumption, coolnvintage, uncrate, throtl, themarket-bonhams, erclassics
- **4 HTML listing feeds registered** for ongoing monitoring: carandclassic, classicdriver, erclassics, autohunter
- **Existing RSS feeds verified flowing**: motorious (25), guyswithrides (10), allcollectorcars (14)
- **Sites onboarded via onboard-source**: classiccars.com (35K already queued), hemmings (286 queued), dupontregistry (onboarded+profiled), autohunter, petrolicious, coolnvintage, uncrate, autotrader, themarket.co.uk, throtl, barnfinds
- **Sites behind Cloudflare (need Playwright)**: classiccars.com (403), cargurus (403/DataDome), autotrader (JS SPA)
- **Throtl confirmed as parts marketplace** (not vehicle listings) — deprioritized
- Total niche collector URLs now in import_queue: ~98K across 18 sources

### [feed] HEAT hero lens — server-powered attention visualization
- Created `hero_heat()` PostgreSQL RPC function: returns top 30 hottest vehicles by heat_score, 30-day comment velocity (top 10), and avg heat by make (min 20 vehicles, top 20 makes)
- Built `HeatHeroPanel` component: scrollable horizontal strip of hot vehicle cards with thermometer bars (blue-to-red gradient), make heat sidebar bars, "Most Discussed (30D)" mini-list
- Built `useHeroHeat` React Query hook with 5-min cache
- Wired heat_score dimension from client-side treemap to server-powered panel in HeroPanel.tsx
- Cleaned up dead client-side bucket functions (buildDealBuckets, buildHeatBuckets, buildFindsBuckets) — all now server RPCs
- Data: 228,985 vehicles with heat scores (range 5-55, p90=15), 13,869 recent comments across 560 vehicles

### [data] BaT 42K URL bulk ingest — 3-phase pipeline
- **STEP 1 COMPLETE**: Created 28,068 new vehicle records from URL slug parsing (Y/M/M extraction)
  - Filtered 12,019 non-vehicles (motorcycles, boats, trailers, memorabilia)
  - Used existing `bat-url-parse-bulk-insert.mjs` — triggers disabled during insert, 1000/batch
  - Also queued 29,998 URLs into import_queue for future deep extraction
- **STEP 2 COMPLETE**: Enriched 1,103 vehicles from existing BaT snapshots via `bat-storage-extract.mjs`
  - Downloaded HTML from Supabase Storage, extracted price/description/VIN/images
- **STEP 3 RUNNING** (PID 69798): `bat-drain-queue.mjs` — single-connection fetch+extract
  - Draining at ~10K/hr, 38.7K remaining, zero rate limiting from BaT
  - Fetches page HTML, extracts JSON-LD/title/meta, updates vehicle (price, desc, VIN, trans)
  - 20 concurrent fetches, 300ms delay, 100 URLs/claim, single persistent DB connection
  - Iterated: bat-extract-direct.mjs (25K/hr fetch but queue not draining), fixed with persistent conn
  - ETA: ~3.9 hours remaining (should complete by ~8 PM)
  - New scripts: `scripts/bat-drain-queue.mjs`, `scripts/bat-extract-direct.mjs`, `scripts/bat-fast-fetch.mjs`, `scripts/bat-fetch-and-extract.mjs`
  - Fixed `vehicle_images` column name (was `url`, actually `image_url`)
- BaT totals: 162,839 vehicles, 79.8% with desc, 81.4% with price, 83.0% with image, 73.8% with VIN

### [discovery] BaT /models/ Full Discovery — 10,942 new listing URLs found
- Discovered BaT's undocumented REST API: `/wp-json/bringatrailer/1.0/data/listings-filter` (277-page limit without session)
- Scraped all 2,439 make/model pages from `/models/` index (401 makes + 2,044 models)
- Extracted embedded JSON items data (24 items per page initial load)
- Found 50,742 total listing URLs, 10,942 not in any DB table
- Queued 10,672 new URLs to `bat_extraction_queue` (pending extraction)
- Gap reduced from ~32,824 to ~16,187 (51% reduction)
- Remaining 16K gap requires Playwright deep crawl on high-count makes (>24 listings)
- Scripts: `bat-models-discovery.mjs` (API crawler), `bat-make-pages-discovery.mjs` (HTML scraper)
- Zero errors, 93.7 minutes runtime

### [condition] Condition Observation Extraction at Scale — 3 data gaps wired
- Migration: Added 'condition' to 6 auction sources + registered 'nuke-vision' source
- Gap 1 (Descriptions): `discover-description-data` now runs condition extraction pass + `condition_backfill` mode
- Gap 2a (Hagerty Comments): `extract-hagerty-listing` extracts comments from __NEXT_DATA__ via ingest-observation
- Gap 2b (Comment Conditions): `batch-comment-discovery` adds Hagerty platform + emits Category B claims as condition obs
- Gap 3 (Vision): `score-vehicle-condition` creates vision_summary + per-concern condition observations via nuke-vision source
- All 4 edge functions deployed, backfill orchestrator: `npm run backfill:condition`
- Content-hash dedup verified (re-run same vehicle = no duplicates)
- Blocked by: Anthropic API credits exhausted — condition extraction works but can't run at scale until credits replenished

### [extraction] Shallow BaT Vehicle Backfill + Comment Gap Fix
- Identified 1,998 BaT vehicles with listing_url but no description/VIN/specs
- 629 had archived snapshots, 1,369 did not (262 were URL normalization mismatches with double slashes)
- Created `scripts/backfill-shallow-bat.mjs` to batch-extract no-snapshot vehicles via extract-bat-core
- Manually extracted K10 (1101eaed) — now has description (481 chars), sale price ($10K), mileage (62K), 33 comments, 76 images
- Fixed comment backfill cron (job 81 was DISABLED, re-enabled at 10min interval)
- Rewrote `backfill-comments` function: replaced 10-page cycling with RPC (`get_unextracted_comment_events`) for O(1) lookup
- Created partial index `idx_vehicle_events_bat_unextracted_comments` for fast unextracted event queries
- Created `get_unextracted_comment_events()` RPC function (SECURITY DEFINER, filters metadata->>'comments_extracted_at' IS NULL)
- Fixed self-continuation bug: function now continues even when some items error (was stopping on any failure)
- Deployed updated backfill-comments function
- Progress: 156 shallow vehicles fixed, 170+ new comment extractions, 22 malformed /carfax URLs skipped
- Comment gap: 809 vehicles missing 52,656 expected comments. ~128K total events still need extraction.
- Backfill running in background, cron will continue

### [discovery] Auction Platform Gap Analysis — coverage audit + 3 new feeds live
- Audited all 111 distinct vehicle sources (356K vehicles) and cross-referenced against source_registry (96 entries), observation_sources (144 entries), and listing_feeds (10 source slugs)
- Researched 22 missing/underserved platforms across 5 tiers: major missing, European auctions, wholesale/salvage, niche/regional, Japanese market
- Probed sitemaps and RSS feeds for 15+ platforms to assess integration difficulty
- **Registered 3 new RSS feeds** in listing_feeds, all tested and confirmed working:
  - AllCollectorCars (active auctions) — 10 items found
  - Motorious (vehicle marketplace) — 15 items queued
  - GuysWithRides (classic car listings) — 10 items queued
- Key findings: biggest gaps are Classic Driver (EU marketplace, 31-page sitemap ready), ClassicCars.com (40K+ listings, only 23 in our DB), The Market by Bonhams (EU BaT equivalent), and AutoHunter (Barrett-Jackson online arm)
- Gap analysis document: `specs_ralph/auction-platform-gap-analysis.md`

## 2026-03-24

### [feed] MV refresh fix + clickable header metrics
- Fixed `vehicle_valuation_feed` MV that was NEVER refreshing (all 16 cron runs failed with 120s timeout)
- Root cause: postgres role had 120s statement_timeout, but 830MB MV refresh needs ~3-5 minutes
- Fix: re-created cron.schedule with `SET statement_timeout = '600s'` prefix
- Forced manual refresh: 344,607 rows now live (2,637 today, 8,805 for sale, 607 live auctions)
- Clickable feed header metrics already wired by prior session — improved:
  - Fixed "LIVE" handler to sort by feed_rank (live auctions get +200 rank boost) instead of duplicating for_sale
  - Added `added_today` filter to feed-query edge function (was in FilterState but never sent to backend)
  - Fixed hover style: 2px borders per design system, removed layout-shifting "FILTER" label
  - Removed redundant welcome strip (stats strip is now the single clickable data bar)
- Deployed feed-query edge function with added_today support
- All TypeScript compiles clean (frontend + Deno)

### [valuation] Barrett-Jackson price gap: 5,903 → 98 vehicles without price signal
- Started with 5,903 BJ vehicles having no sale_price AND no nuke_estimate
- Investigated snapshots: all 1,408 show "Register to View Price" (BJ paywalls prices behind login)
- No hammerPrice in archived HTML — BJ Next.js RSC only sends price data to authenticated users
- Ran comp-based valuation via compute-vehicle-valuation for 4,965 eligible vehicles
- 4,875 successfully computed (98.2% success rate), 90 too obscure for comps
- Remaining 98 are un-valueable oddities: buggies, covered wagons, paddle boats, fire trucks, boat trailers
- BJ coverage: 99.74% of 38,244 vehicles now have a price signal (sale_price or nuke_estimate)

### [data-quality] FB Saved Vehicles deep enrichment — 483 vehicles, 6,594 evidence rows
- **Before**: 483 title+price skeletons from Mar 16 FB Saved Items import. Only 7 had descriptions, 0 AI-enriched.
- **Phase 1**: Propagated 38 marketplace_listing descriptions + images to vehicle records
- **Phase 2**: Regex-parsed 45 descriptions for VIN, engine, transmission, drivetrain, body_style (31 new fields extracted)
- **Phase 3a**: Rule-based enrichment for ALL 483 vehicles (329 fields: body_style +157, drivetrain +164)
- **Phase 3b**: Ollama qwen2.5:7b AI extraction for ALL 483 vehicles (2,207 evidence rows: trim, engine, condition, features)
- **Cleanup**: Fixed 4 non-vehicles (parts), corrected 5 missing models, 6 missing years
- **After**: body_style 119→366, drivetrain 101→342, engine 114→155, transmission 138→145, trim 183, vehicle_type 483/483
- Scripts: `enrich-fb-batch.mjs` (3-phase pipeline), `enrich-fb-rules.mjs` (deterministic rules)
- FB listings confirmed unfetchable (bingbot returns login page now)

### [images] Snapshot image extraction — 90K+ images for 16K vehicles
- Created `scripts/extract-images-from-snapshots.mjs` + SQL function `find_imageless_with_snapshots()`
- Phase 1: Promoted 12,306 `primary_image_url` values to `vehicle_images` rows
- Phase 2: Extracted 77,942 images from archived HTML snapshots across 5 platforms
  - Barrett-Jackson: 1,610 vehicles, 16,766 images (91.4% coverage, up from 64.7%)
  - Craigslist: 819 vehicles, 18,852 images
  - Bonhams: 716 vehicles, 716 images (82.4% coverage, up from 39.5%)
  - RM Sotheby's: 489 vehicles, 23,956 images
  - BaT: 356 vehicles, 17,457 images
- Overall vehicle image coverage: 84.6% (298K/353K), up from ~81%
- Remaining gap: 54.5K vehicles, mostly pcarmarket (5.5K, 0 snapshots), mecum (4.5K, "Gallery not available"), KSL (3K, no snapshots)
- Mecum + Gooding snapshots have JS-rendered galleries — images not in HTML

### [valuation] FB Marketplace nuke_estimate sweep — 28% to 44%+ and climbing
- **Diagnosis**: 12,430 FB vehicles appeared to have "no price" (no sale_price + no nuke_estimate)
  - Reality: 99.6% already had asking_price; only 103 truly had no price signal
  - Root cause 1: Valuation cron queue had 42K vehicles across all sources; FB deprioritized
  - Root cause 2: Denorm bug — 337 vehicles had nuke_estimates rows but NULL on vehicles table
  - Root cause 3: Edge function cached path didn't re-denormalize, causing infinite cron retry
- **Fix 1**: Backfilled 337 denorm gaps (UPDATE vehicles FROM nuke_estimates)
- **Fix 2**: Fixed compute-vehicle-valuation cached path to re-denormalize on cache hit
- **Fix 3**: Deployed targeted FB sweep (200 batches x 100 vehicles, running in background)
- **Results so far**: nuke_estimate coverage 28% → 44% (12,717 of 29K), sweep continuing
- **Error rate**: ~14% per batch from junk data (make="3", "Hemi Veney", etc.)
- Deployed: compute-vehicle-valuation with denorm fix

### [data-quality] Facebook Marketplace Deep Enrichment Pipeline
- **Problem**: 29K FB vehicles were shallow — 13% descriptions, 47% prices (initially reported), 0% VINs
- **Root cause**: Scraper only captured search-page data (title, price, image); descriptions require individual page visits
- **Quick wins applied immediately**:
  - Propagated 73 descriptions from marketplace_listings to vehicles
  - Propagated 662 locations from raw_scrape_data to vehicles (72.1% coverage now)
  - Filled 6 missing prices from raw_scrape_data (prices were actually 99.4% already)
- **Fixed bingbot->Googlebot UA** in refine-fb-listing (Facebook blocked bingbot as of 2026-03)
- **Discovered**: Cloud-based scraping (Supabase Edge Functions) blocked by FB — redirects to login from non-residential IPs
- **Added Phase 2 title-parse fallthrough** to refine-fb-listing for listings without descriptions
- **Upgraded refine cron**: 2x/hr batch_size=15 -> every 5 min batch_size=50
- **Added tier 0 (all years)** to enrich-fb-ollama.mjs
- **Fixed listing_url unique constraint error** in fb-enrich-all.ts
- **Started Playwright enricher** (PID 98827): ~450 vehicles/hr, getting descriptions + structured fields from residential IP
- **Started Ollama enricher** (PID 98175): ~720 vehicles/hr, AI title extraction for vehicle_type/trim/engine/transmission
- **Projected**: 25K descriptions via Playwright (~56 hrs), 19K AI title enrichments via Ollama (~27 hrs)

### [data-quality] Barrett-Jackson VIN Extraction from Snapshots
- Extracted 2,180 VINs from B-J `listing_page_snapshots` markdown using pattern `([A-Za-z0-9]+) Vin`
- Script: `scripts/backfill-bj-vins.mjs` (npm: `backfill:bj-vins`)
- VIN confidence: 90 for 17-char modern VINs, 80 for shorter chassis numbers
- B-J VIN coverage improved from 19.2% to 27.2% (19,849 of 72,849 vehicles now have VINs)
- 11,564 vehicles had matching snapshots but VINs already existed on other vehicle records (B-J duplicates)
- Remaining 53K VIN-less: 32K conceptcarz imports (no B-J URL), 12.9K have B-J URL but no snapshot, 8K discovery_url only
- Handles two unique constraints: `vehicles_vin_unique_17char` (vin alone) and `vehicles_vin_unique_short` (vin+make)
- Safely disables `trigger_auto_detect_duplicates` and `auto_vin_decode_trigger` during batch updates, re-enables in finally block

### [data-quality] Barrett-Jackson Description Backfill
- Extracted descriptions from 39K archived markdown snapshots in listing_page_snapshots
- Matched snapshots to vehicles via listing_url (direct) and vehicle_events.source_url (fallback), with www normalization
- BJ markdown structure: Description > ## Summary (short) > ## Details (full prose)
- **3,105 vehicles** updated with prose descriptions (avg ~1,100 chars)
- **105 vehicles** had snapshots but only structured fields, no prose
- Gap reduced from 47,035 to 43,930 (remaining 43.9K are conceptcarz imports without BJ URLs)
- Script: `scripts/backfill-bj-descriptions.mjs` with 1000-row batches, pg_sleep, lock checking
- npm scripts: `backfill:bj-descriptions`, `backfill:bj-descriptions:dry-run`

## 2026-03-23

### [data-quality] Data Enrichment Sprint — VERIFIED
- **Platform source**: 5K → 201K (+196K). 25 platforms tagged from listing_url patterns
- **Color family**: 142K → 207K (+65K). 14 families. Two-tone fix (9.5K reclassified)
- **Displacement**: 67K → 104K (+37K) from vin_decoded_data backfill
- **Seller name**: 0 → 64K from bat_seller propagation
- **Transmission**: 62K normalized (case, format, junk removal)
- **VIN decode total**: +65K cells (displacement 37K, fuel 9.4K, trim 8.8K, doors 7.8K, engine 1.4K)
- **Mileage from descriptions**: +3.1K regex-extracted. Cleaned 93 outliers >500K
- **Make normalization**: 686 fixed (lowercase, abbreviations)
- **Location/price/date**: +2.3K from bat_ field propagation
- **Cron scaling**: BaT extraction 3x (5→15), VIN decode 4x (50→100, 30→15min)
- **Validation**: 9 tests, all pass. 0.005% platform mismatch. VIN 15/15 spot checks correct
- Scripts: enrich-vehicles, normalize-transmission, normalize-makes, tag-platform-source, backfill-vin-decode

### [infra] Presigned URL Photo Upload Architecture (5 phases)
- Migration: upload_batches + upload_batch_items tables
- Server: image-intake prepare_upload/confirm_upload actions. E2E tested + deployed
- CLI: scripts/lib/presigned-upload.mjs. Refactored bulk-photo-upload + nuke-photo-drop
- Browser: nuke_frontend/src/lib/uploadClient.ts. Refactored PhotoSyncPage
- MCP: mcp-connector ingest_photos → presigned for base64 images

### [auction-pipeline] Live Auction Fixes
- 5K vehicle_images backfilled from thumbnails + auto-create on sync
- Comment extraction: 6h→24h, 10→25 batch, soonest-first sort
- Bid snapshots, new auctions, comments, images — all 4 verified working

### [infra] .claude/ Full Restructure (27GB → 12MB)
- [cleanup] Deleted 18 stale worktrees (~27GB), archived 40+ stale files
- [rules] 7 path-scoped rules: db-safety, extraction, edge-functions, frontend, library, agent-coordination, platform-hygiene
- [commands] 7 slash commands: /status, /extract, /deploy, /health, /library, /qa, /debug-all
- [settings] Project settings.json created. MEMORY.md trimmed 239→100 lines.

### [extraction] BaT Auth Redirect Bug Fixed + Deployed
- [fix] extract-auction-comments + extract-bat-core patched and deployed (v137, v107)
- [audit] 36/40 extractors vulnerable to same redirect bug — EXTRACTOR_REDIRECT_AUDIT.md

### [audit] 5 Platform Audit Reports
- FRONTEND_AUDIT.md, EXTRACTOR_REDIRECT_AUDIT.md, DESIGN_VIOLATIONS.md (1,641 violations), LIBRARY_GAP_ANALYSIS.md, ISSUES.md updated

### [qa] QA Closed Loop — /qa and /debug-all commands, ISSUES.md tracker, sentinel updated

### [wiring] Overnight Sprint — Book, Data Validation, Pin Map Fix
- **13 book chapters written** (Ch2, Ch4, Ch9-12, Ch13-15, Appendices A-D) — book now 15/15 complete
- **GM circuits 109 → 219**: 110 new circuits from manual pages 8C-46 to 8C-51
- **Invoices 33 → 49**: SW77005 + SW77006 line items ingested
- **Factory circuit cross-ref**: 40 MATCH, 3 corrections (speaker L/R, washer pump colors)
- **CRITICAL: M130+M150 pin maps REPLACED**: All 180 scaffolded pins were WRONG — replaced with MoTeC datasheet data
- **Key discovery**: M150 Connectors C+D = M130 Connectors A+B (identical pinout = easy upgrade path)
- Knowledge doc updated, corrections log complete (17 total corrections)

## 2026-03-22

### [build-intel] K5 Blazer Build Intelligence System
- **build_activity_snapshots table**: Monthly aggregates combining QB spending + photo activity + manifest purchases
- **compute-build-timeline edge function**: Computes 42 months of activity data for K5 ($81K, 516 photos, peak Jan 2022)
- **enhance-qb-confidence edge function**: Enhanced 131 QB transactions with temporal/photo/vendor correlation (11 high, 81 medium, 39 low)
- **compute_build_spend_profile() SQL function**: Comprehensive build spend analysis — by_category, by_month, by_vendor, manifest stats
- **pipeline_registry**: 6 new entries for computed fields
- **Frontend BUILD section**: BuildManifestPanel (categorized parts list), BuildTimelineChart (monthly spend + photo overlay), BuildSpendSummary (top-line numbers)
- **useBuildProfile hook**: Parallel fetch of manifest, snapshots, and spend profile via RPC
- **WorkspaceContent.tsx**: BUILD MANIFEST + BUILD TIMELINE widgets inserted after Pricing & Value, gated behind owner/contributor access

### [wiring] LS Swap Template + K5 Wiring Overlay
- **seed-ls-swap-template.mjs**: Creates "LS Swap - Motec M150 + PDM30" template (121 new circuits, 71 factory circuit actions)
- **create-k5-wiring-overlay.mjs**: Links template to K5, calls compute-wiring-overlay (110 wires, 804 ft)
- npm scripts: `wiring:seed-template`, `wiring:create-k5-overlay`

### [materialization] Field Evidence Materialization
- **materialize-field-evidence.mjs**: Reads pending field_evidence, applies trust hierarchy, writes to vehicles + provenance
- Dry-run validated: 23K pending fields, 3.1K vehicles, 257 conflicts resolvable
- npm scripts: `materialize:field-evidence`, `materialize:field-evidence:apply`

### [bedrock] ARS Batch + Node.js Script
- ARS batch: 2,142 → 323,287 scored (100% of all vehicles). COMPLETE. 186 NEEDS_WORK, 24,728 EARLY_STAGE, 298,373 DISCOVERY_ONLY. 321,145 new scores in one session across 72 batches.
- `scripts/batch-ars-scoring.mjs` — per-vehicle commit Node.js script (no transaction rollbacks)
- npm scripts: `ars:batch` (continuous 5K), `ars:batch:small` (1K)

### [oem-reference] OEM Reference Book — Cited Sources Import
- **EPA Fuel Economy**: 44,523 specs (1984-2026, 146 makes). Engine, trans, drivetrain, MPG. Source: `EPA_fueleconomy_gov` conf:90
- **NHTSA Vehicle Catalog**: 13,340 specs + 1,279 model defs (1981-2000, 44 makes). Source: `NHTSA_VPIC` conf:95
- **Normalization Rules**: 36 total (was 18). 107 variant mappings across 7 field types. Mined from 175K+747K evidence rows.
- **auto_populate_vehicle_specs()**: Upgraded to 4-strategy fuzzy matching (exact→prefix→contains→stripped-suffix)
- **oem_vehicle_specs**: 14 → 57,877 rows | **oem_models**: 15 → 1,294 rows
- Scripts: `oem:epa`, `oem:nhtsa`, `oem:normalize` in package.json

### [bedrock] Deep System Audit + 8 Priority Deployments
- **Temporal decay DEPLOYED**: `observation_half_lives` table (14 kinds), `compute_decayed_confidence()` function, `vehicle_observations_decayed` view, `get_effective_observations()` function. Theory→production in 1 step.
- **Conflict resolution DEPLOYED**: `vehicle_field_consensus` table + `detect_field_conflicts()` function. Found 4 real conflicts in top 50 vehicles (4x4 vs 4WD, mileage discrepancy).
- **Cross-vehicle image matching DEPLOYED**: `dhash_hamming_distance()`, `find_similar_vehicles()`, `find_image_duplicate_candidates()`. Found 5,000+ exact image matches (hamming=0) across 18K fingerprints.
- **ARS batch computed**: 10,142 vehicles scored (was 2,142). 7 NEEDS_WORK, 2,046 EARLY_STAGE, rest DISCOVERY_ONLY. Running continuously.
- **YONO sidecar REVIVED**: `modal deploy yono/modal_serve.py` — all models healthy (276 flat classes, 41 zones, finetuned_v2 vision).
- **Digital twin engine proof**: 1977 Blazer (CKR187F127263) fully seeded across 8 engine tables: block (400ci SBC #3951509), 2 heads (336781 76cc), crank (#3932442 externally balanced), cam (flat-tappet hydraulic), Q-Jet carb (#7047213), dual-plane intake (#346250), HEI distributor, oil system. First complete engine digital twin.
- **Background**: RPO library enrichment + Haiku comment mining running

### [pipeline] FB Saved Items → Supplier Inventory Pipeline
- **Migration**: `20260322220000_supplier_pipeline.sql`
  - Expanded `organization_vehicles.relationship_type` CHECK: +supplier_inventory, supplier_sold, supplier_build
  - Added `fb_saved_items.is_supplier_listing` boolean column
  - Expanded `fb_saved_items.processing_status` CHECK: +queued, imported
  - Created `supplier_vehicle_readiness` view (org_vehicles × ARS scores)
- **Phase 1**: `scripts/enrich-fb-orgs.mjs` — enriches 73 FB stub orgs (Firecrawl FB page + Google search → create-org-from-url)
- **Phase 2**: `scripts/catalog-supplier-inventory.mjs` — 3 inventory sources:
  - A: Website inventory via discover-organization-full
  - B: Marketplace cross-link (fb_saved_items → import_queue)
  - C: Reel title parsing for vehicle references → organization_behavior_signals
- **Phase 3**: `scripts/monitor-supplier-inventory.mjs` — 3 monitoring loops:
  - A: Weekly website re-scrape scheduling
  - B: FB Marketplace supplier matching
  - C: FB Saved items status dashboard
- **Phase 4**: Wired supplier vehicles to ARS pipeline via `supplier_vehicle_readiness` view
- **npm scripts**: supplier:enrich, supplier:catalog, supplier:monitor (+ :dry variants)
- **Execution results:**
  - Phase 1: 59 enriched, 50 with verified websites, 14 with phone, 5 with email, 6 with address
  - Phase 2B: 747 marketplace items → import_queue (63 vehicles created, 8K non-vehicles skipped)
  - Phase 2C: 18 vehicle references from 93 reels across 15 organizations → behavior signals
  - Phase 3: 50 orgs in inventory sync queue, monitoring dashboard operational
  - Cleaned 10 false-positive website matches (generic sites from Google search)

### [infra] Presigned URL Photo Upload Architecture
- **Migration**: `upload_batches` + `upload_batch_items` tables, `vehicle_images.upload_batch_id` column
- **Server**: `image-intake` edge function now supports 3 actions:
  - `prepare_upload` — dedup-check hashes, generate presigned URLs (up to 500/call)
  - `confirm_upload` — batch-INSERT vehicle_images for completed uploads
  - (default) — legacy flow unchanged
- **CLI library**: `scripts/lib/presigned-upload.mjs` — hash, request URLs, parallel PUT, confirm batch
- **Browser client**: `nuke_frontend/src/lib/uploadClient.ts` — Web Crypto hashing, concurrent PUT, progress
- **Refactored**: `bulk-photo-upload.mjs`, `nuke-photo-drop.mjs` → use presigned upload lib
- **Refactored**: `PhotoSyncPage.tsx` → uses `uploadClient.ts` (50 concurrent, presigned)
- **Refactored**: `mcp-connector/index.ts` `ingest_photos` → presigned flow for base64 images
- **Flow**: Client hashes → prepare_upload → PUT direct to storage → confirm_upload → batch INSERT
- **Result**: 1,500/hr → 15,000-30,000/hr per user (bytes never touch our server)
- **TOOLS.md** updated with presigned upload entries

## 2026-03-21

### [social] Patient Zero — Autonomous Daily Posting System
- **3 tables created**: `patient_zero_queue` (post state machine), `patient_zero_image_pool` (curated images), `patient_zero_config` (per-account settings)
- **Edge function deployed**: `patient-zero` — single action-routed function handling generate/publish/preview/approve/skip/override/stats/pause/curate/seed_pool + Telegram webhook
- **Telegram webhook registered**: `/pz`, `/pzskip`, `/pzstats`, `/pzpause`, `/pz override <text>`, inline Approve/Skip buttons
- **2 cron jobs**: `patient-zero-generate` (daily 1pm UTC), `patient-zero-publish` (every 5 min)
- **Image pool seeded**: 50 random pre-1990 vehicle primary images for X account (@1991skylar)
- **Config seeded**: X account enabled (manual approval), IG account disabled (awaiting OAuth fix)
- **Day 480 generated**: "day 480. 1988 jeep wrangler sahara 5-speed. nobody noticed yet." — Telegram preview sent, approved via API test
- **Caption gen**: Haiku 4.5 via llmRouter, ~$0.001/caption, dry deadpan format enforced by system prompt
- **TOOLS.md updated**: Full Social Media & Posting section added
- Day 1 = Nov 28, 2024. Count climbs autonomously. Zero human input per day.
- **v2 improvements (same session):**
  - x-media-upload migrated from v1.1 → v2 endpoint (`api.x.com/2/media/upload`), v1.1 sunset June 2025
  - Alt text auto-generated from vehicle year/make/model/color, passed via x-media-upload to X
  - Media uploaded separately (with alt text) then attached via media_ids — avoids double-upload
  - Telegram webhook secured with `secret_token` (401 for unauthenticated requests verified)
  - Telegram bot commands registered via `setMyCommands` (/pz, /pzstats, /pzskip, /pzpause in menu)
  - Bluesky publishing support added (AT Protocol: session auth → blob upload → createRecord with richtext facets)
  - Threads publishing support added (graph.threads.net: container → publish)
  - Instagram upgraded to Graph API v25.0, uses `graph.instagram.com` endpoint (was `graph.facebook.com`)
  - Instagram: `?format=origin` appended to Supabase Storage URLs to prevent WebP auto-conversion
  - Instagram: hashtags in caption (3-5 max, current best practice) instead of first comment
  - X: 1.5s delay between main post and hashtag reply to avoid rate limit issues
  - TOOLS.md updated with platform details and security notes

### [data-quality] Autonomous Data Quality & Pipeline Session
- **Mecum URL normalizer fixed**: `mecum:lots/303124/slug` → `mecum:303124` (lot number only). False-positive dup groups dropped from 551 → 48.
- **RM Sotheby's URL normalizer fixed**: Now includes auction event code. `rmsothebys:r0019-slug` → `rmsothebys:pa25:r0019-slug`. Prevents cross-event collisions.
- **SQL `normalize_listing_url()` function updated**: Matches TS changes. Applied via migration `20260321190001`.
- **3 edge functions deployed**: `ingest-observation`, `dedup-vehicles`, `extract-jamesedition` — all carry updated URL normalization.
- **Hero fingerprints scaled**: Concurrency 20→50, batch 500→2000. 50K batch launched in background (PID 43633).
- **FB Marketplace → Vehicle pipeline**: `scripts/fb-marketplace-to-vehicles.mjs` built. 192 listings linked (124 new vehicles + 68 existing matches), 299 empty stubs marked reviewed, 0 errors.
- **Ghost record triage**: 8,084 zero-data ghosts archived (no URL/images/VIN/year). 89.6K image-bearing ghosts identified as fingerprint priority targets.
- **Weekly dedup cron**: `scripts/scheduled/weekly-dedup-sweep.sh` created. Runs normalized URL dedup + VIN duplicate detection. Target: Sunday 3am.
- **New npm scripts**: `fb:link-vehicles`, `dedup:weekly`

### [search] Complete Search Rebuild — Frontend + Backend Deep Search
- **Search page rewritten**: 1,293 lines → 75 lines. Removed duplicate search bar, VIN lookup button, "Barn find"/"Manual transmission" pills, GPT-4o answer box, inline haversine, vibe detection, workstation quick-links
- **New files**: `useSearchPage.ts` (hook), `useSearchEmptyState.ts` (hook), `SearchFilterPanel.tsx`, `SearchStatsBar.tsx`, `SearchEmptyState.tsx`
- **Deleted**: `IntelligentSearch.tsx` (93KB) — redundant with header search + useSearch hook
- **Empty state**: data-driven browse facets (top 12 makes with counts, eras, body styles), search tips, notable sales grid, recently added grid, total vehicle count hero
- **Browse stats**: when searching a make, shows total/avg price/model breakdown/source distribution/era distribution (expandable)
- **`vehicle_search_index` table**: denormalized FTS combining vehicle fields (weight A), descriptions (B), comments (C), evidence (D) with GIN index. 556K rows populated.
- **`search_vehicles_deep` RPC**: searches across ALL sources, returns match_source + highlighted snippets via `ts_headline`. Ranking boosted for make/model field matches (+5.0 for exact make, +4.0 for make+model prefix).
- **`search_vehicles_fuzzy` RPC**: trigram fuzzy fallback for typo tolerance ("camero" → Camaro). Triggered when FTS returns < 3 results.
- **universal-search edge function**: updated to call deep search + fuzzy fallback in parallel. Results enriched with `deep_match_source` and `deep_snippet` metadata.
- **SearchResults.tsx**: vehicle cards now show match provenance snippet (COMMENT/DESCRIPTION/EVIDENCE label + highlighted text)
- **Comment aggregation**: 28K+ vehicles have aggregated comment text indexed (still running, batch job in background)
- **Quality audit**: 12 test queries run. Fixed: Porsche ranking noise (MG no longer appears), typo tolerance working, multi-field matching confirmed (description + comment cross-matching)
- **Deployed**: universal-search edge function, frontend build clean

### [frontend] Browser Inspection + Fixes from Live Site
- **OPEN PROFILE → button fix**: was missing from expanded cards (expandedContent || fallback logic bug)
- **Auctions recently-ended**: always loads independently now (was gated on results.length === 0)
- **Data discovery**: `feed_rank_score` and `deal_score_label` don't exist on vehicles table — only computed by feed-query edge function. Search page sections querying these columns got zero results.
- **Deployed to production** via git push

### [schema/frontend] Comment System Unification — Phases 0-2
- **Root cause:** Vehicle profile "Comments & Bids" widget was hidden because count query checked `vehicle_comments` (26 rows) instead of `auction_comments` (11.55M rows)
- **Created `user_comments` table:** Consolidates `vehicle_comments` (26), `vehicle_image_comments` (5), `timeline_event_comments` (1) into single polymorphic table with `target_type` + `target_id`. RLS policies mirroring old tables.
- **Created `vehicle_comments_unified` VIEW:** UNION ALL across `auction_comments` (11.55M) + `user_comments` (30) + `vehicle_observations` where kind IN (comment, bid) (605K, deduped against auction_comments via NOT EXISTS). LEFT JOIN for null source_ids. Per-vehicle count query: 1.6ms.
- **Added partial index:** `idx_observations_vehicle_comment_bid` on vehicle_observations(vehicle_id, observed_at DESC) WHERE kind IN (comment, bid) — dropped observation arm from 284ms to 2.7ms.
- **Frontend:** `VehicleProfileContext.tsx` now counts from unified VIEW. `VehicleCommentsCard.tsx` reads from single VIEW query (was 3 parallel table fetches). Realtime subs reduced from 3 to 2 (auction_comments + user_comments). Write path: post/edit now targets `user_comments`.
- **Extraction:** Removed `bat_comments` upsert from `extract-auction-comments` edge function. `auction_comments` is now sole write target.
- **Deferred:** `CommentService.ts` (timeline event comments) — has richer per-event fields (image_id, work_order_id, context_type) needing schema consideration. `profileStatsService.ts` — queries bat_comments with JOINs to bat_listings, needs separate refactor.

### [frontend] Click-to-Expand Cards + Zero Dead Ends (Phases 3-5)
- CardShell: single click expands card in-place instead of navigating away
- Expanded view shows BadgePortals for every vehicle dimension (year, make, model, body, trans, deal, source)
- Explicit "OPEN PROFILE →" button for navigation. Cmd/Ctrl+click → new tab.
- VehicleHeroImage no-photo state: shows vehicle identity + BadgePortals instead of black void
- BarcodeTimeline empty: suggests comparable vehicles
- PriceHistoryModal empty: explains data accumulation
- FeedEmptyState: always links to Search + Auctions (no dead ends)
- DetailPanel component created (slide-in overlay, not yet wired to feed)

### [frontend] BadgePortal System — End-to-End Design Foundation
- `BadgePortal` component: every badge is clickable, expands inline cluster panel, collapses back
- `BadgeClusterPanel`: 6-item preview grid with vehicle thumbnails, prices
- `useBadgeDepth`: lazy depth+preview fetch with 200ms debounce and cache
- VehicleSubHeader YMM badges → BadgePortals (no more navigate-away context destruction)
- CardDealScore pills → BadgePortals (click STEAL → see all steals inline)
- Supports: year, make, model, source, deal_score, status, body_style, drivetrain, transmission

### [frontend] Bug Fix Sprint — Tier 1+2 (13 bugs, 12 files)
- **#7** Hero image black void: added fallback query (any non-doc/non-dup image)
- **#14** Search default: sort by feed_rank_score instead of sale_price desc
- **#20** Auctions page: shows "Recently Ended" (30d) when no live auctions
- **#11** Price history modal: falls back to vehicle_events prices
- **#9** Timeline: shows "NO TIMELINE DATA" instead of empty grey boxes
- **#1** ResilientImage: cleaner "IMAGE UNAVAILABLE" fail state
- **#2** Grid card height: bumped from 320→340px for badge space
- **#3** Deal badges: added tooltip explanations (STEAL, GREAT DEAL, etc.)
- **#4** Source favicons: added platform name labels (FB MARKET, BAT, etc.)
- **#6** Stats strip: shows "SHOWN X / Y" when filtered
- **#8** Gallery alt text: uses photo ID instead of generic "Vehicle image"
- **#12** "MULTI-SOURCE VERIFIED": requires 5+ multi-source fields (was 75% coverage)
- **#13** Dossier SRC badges: collapse to "Nx" when not hovered

### [mcp] User Onboarding & Account Linking — 5 new MCP tools
- `create_profile`: email → Supabase auth user + profile + API key (idempotent)
- `get_profile`: lookup by email/user_id with vehicle count + linked accounts
- `link_account`: connect BaT/C&B/Hemmings/Hagerty/Instagram/YouTube/Facebook/eBay/Craigslist with preview of linkable data
- `verify_account_link`: email_match, profile_url_proof, or manual_review verification pipeline
- `list_linked_accounts`: unified view of all linked platforms + pending claims
- DB: `mcp_create_api_key` RPC, `account_link_claims` table, `onboarded_via` on profiles, `submitted_by_user_id` on vehicle_observations
- Fixed `create_user_rating_on_signup` trigger (missing `SET search_path TO 'public'` was blocking ALL auth user creation)
- Extended `user_external_profiles` platform check constraint (was only 5 platforms, now 14)
- MCP connector: 28 → 33 tools. mcp-server npm: 7 → 12 tools
- All tools tested end-to-end: create → lookup → link → verify → list

### [data-integrity] Comment→Identity Linking + Engagement Stats
- **11.6M auction_comments linked** to external_identities via `author_external_identity_id` (was 0% → 99.9%)
- `external_identity_id` backfill running (46K+ done in first batch)
- Created `idx_auction_comments_author_username` index for fast join
- Built `identity_engagement_stats` materialized view: comments, bids, expertise score, activity per handle
- `link_account` MCP tool now shows engagement preview from matview
- RPO library: 23 → 174 codes (engines, transmissions, axles, suspension, packages, 1955-2010)
- Skylar profile: location set to Boulder City NV, 41 vehicles linked by owner_id
- Data integrity audit: 20K orphan images, 62K vehicles w/o snapshots, 752 vehicles w/o events

### [pipeline] Markdown Bridge + AI Extraction
- 5 markdown bridges launched in parallel: BaT, BJ, Mecum, C&B, Bonhams
- BJ AI extraction: 53+ vehicles extracted, 2.2 avg fields, $0.01 cost, zero errors

## 2026-03-20

### [frontend] Vehicle card image rendering fix + AVG PRICE fix
- [bug] Fixed grey/empty image boxes in vehicle grid: Supabase render API returns 422 "Invalid source image" for large files (5MB+ Facebook photos). Fixed by adding original URL as fallback source in `ResilientImage.normalizeSources` — render fail → retry with raw storage URL
- [bug] Fixed "AVG PRICE $0" in feed stat card: `portfolio_stats_cache.avg_value` was 0. Fixed in DB (set to $32,646) + fallback computation in feed-query
- Files: `nuke_frontend/src/components/images/ResilientImage.tsx`, `supabase/functions/feed-query/index.ts`
- Deployed to prod

## 2026-03-21

### [overnight] Autonomous Overnight Session (2026-03-21 00:00-08:00)

**Stabilize + Commit:**
- [git] Committed 12 files: overnight scripts, listing package generator, MCP connector, mining scripts, package.json updates
- [cron] Fixed job 413 (refresh-vehicle-census): created `idx_vehicles_canonical_platform_v2` including `pending_backfill` status, dropped old index. Matview refresh now <7s (was timing out at 120s)
- [cron] Job 414 (review-agent-submissions): verified already succeeding — no action needed

**Database Cleanup:**
- [vacuum] VACUUM ANALYZE on 11 tables: vehicles (11.7%→0.1%), vehicle_agents (15.1%→0%), listing_page_snapshots (10.3%→0%), transfer_milestones (10.4%→0%), snapshot_extraction_queue (12.1%→0%), ownership_transfers (13.0%→0%), vehicle_live_metrics (10.9%→0.2%), external_identities (6.2%→0%), bat_crawl_state (10.1%→0%), vehicle_status_metadata (8.3%→0%), vehicle_reference_links (7.8%→0%)
- [indexes] Dropped 607 unused indexes (zero scans in 3 weeks): 2548→1942 total indexes. Remaining 1123 zero-scan are PKs/unique constraints (cannot drop). Reclaimed ~450+ MB
- [tables] Audited 115 empty tables: all are digital twin ontology placeholders (engine_blocks, brake_calipers, etc.) — correctly kept

**Data Enrichment:**
- [price] Backfilled sale_price from canonical_sold_price for active vehicles
- [vin] Created `validate_vin_check_digit()` SQL function. Extracted and validated 48 VINs from vehicle descriptions using check digit verification. Skipped duplicates and false positives
- [extraction] Reset 28,129 failed extractions to pending (all had good snapshots — Mecum 18.7K, BaT 7.6K, Bonhams 1.6K). Queue: 26,868 failed → 1 failed
- [extraction] Released 597 stale processing locks (claimed >30min ago)

**Reference Library Expansion:**
- [rpo] Mined 41 new RPO codes from BaT descriptions: Z06, ZR1, ZR2, F41, B4C, FX3, etc. (802→843)
- [library] Promoted 272 staging entries: 58 RPO codes (→901), 38 paint codes (→3,497), 15 trim packages (→594)
- [library] Background Ollama mining stream produced 2,754 new entries in 24h (513 option codes, 244 paint codes, 764 known issues, etc.)

**Final Health Check:**
- Lock waiters: 0
- Dead tuple peak: <5% across all tables (was 17.8%)
- Failed crons (last 6h): 0
- Extraction queue failed: 1 (was 26,868)
- Indexes: 1942 (was 2548)
- DB size: 71 GB (index space reclaimed, but new data from running streams offset savings)
- 4 background streams still running (mining, extraction, snapshots, enrichment)

### [extraction] Overnight Pipeline Infrastructure + Launch (2026-03-20 07:30-08:00)
- [scripts] Added Ollama/Gemini multi-provider support to `mine-comments-for-library.mjs` (--provider ollama|gemini|anthropic)
- [scripts] Created `scripts/run-mine-library.sh` — mining loop wrapper with auto-stop after 5 zero runs
- [scripts] Created `scripts/promote-library-extractions.mjs` — staging → canonical library promotion
- [scripts] Created `scripts/overnight-run.sh` — master orchestrator (4 streams + post-processing + morning report)
- [library] Promoted 2,267 existing staging entries: 342 RPO codes, 98 paint codes, 159 trim packages to canonical tables
- [npm] Added 8 npm scripts: mine:ollama, mine:anthropic, mine:stats, mine:loop, promote:library, promote:library:dry, promote:library:stats, overnight
- [launch] 4 overnight streams running: snapshots (regex), mining (Ollama), extraction (Ollama), enrichment (DB)
- [note] Gemini API key expired — Stream E (high-value Gemini extraction) skipped. All LLM via Ollama.
- [modal] Deployed `nuke-vllm` — Qwen2.5-7B on T4 via Modal ($0.59/hr, 2 containers, scales to 0). `yono/modal_vllm_serve.py`
- [modal] Added `--provider modal` to both mining and extraction scripts. Redirected streams to Modal.
- [modal] URL: `https://sss97133--nuke-vllm-serve.modal.run` (OpenAI-compatible API)
- [npm] Added `mine:modal`, `discover:modal` npm scripts

### [overnight-ops] Overnight Ops Session (2026-03-20 01:00-02:30)
- [critical-fix] Disabled `refresh_tier_on_image_upload` trigger on vehicle_images — references dropped `vehicle_receipts` table via `calculate_platform_tier_score` chain. Was blocking ALL photo intake inserts with `documented_by_user_id`.
- [design] Committed 430+ design system component fixes (border-radius, boxShadow, font enforcement) across nuke_frontend
- [deploy] Deployed 3 edge functions: db-stats, extract-mecum, refine-fb-listing
- [infra] Added error logging to iphoto-intake.mjs (upload + insert errors were silent)
- [data] Album intake RUNNING: 72 albums queued, 5 completed, 42 new photos uploaded (iphoto: 1,686→1,728). ETA ~6 AM.
- [db] DB health verified: 0 lock waiters, all 32 vehicles triggers enabled, broken `trigger_update_primary_focus` already fixed

### [overnight-batch] Overnight Batch Run (2026-03-20 08:00-09:00)
- [design] Global CSS enforcement: `* { border-radius: 0 !important; box-shadow: none !important; }` in unified-design-system.css
- [design] src/pages/ cleanup: 7 files, 0 violations remaining (borderRadius, boxShadow, gradients, shadows)
- [design] src/components/ cleanup: 20+ files, 0 violations remaining (boxShadow, gradients, borderRadius, CSS-in-string, dead transitions)
- [infra] Fixed `review-agent-submissions` cron: `get_service_url()` hardcoded URL (was reading missing GUC). 0 failures since fix.
- [infra] Deleted 12 dead edge functions (10 widget-*, concierge-webhook, pipeline-dashboard). Active: 243→231.
- [data] FB Marketplace national sweep: 58 metros, 4,608 scanned, 1,610 vintage vehicles upserted
- [data] primary_image_url backfill: 61%→88.5% (256,530/289,926 active vehicles). Remaining 33K have zero images.

### [auction-readiness] Auction Readiness System — Sprint 1+2 (2026-03-20)
- [schema] Created `auction_readiness`, `ars_tier_transitions`, `photo_coverage_requirements` tables
- [schema] Created `idx_vehicle_images_vehicle_zone(vehicle_id, vehicle_zone)` index on 33M rows
- [schema] Seeded 20 photo zones (8 required MVPS + 12 competitive CPS) with coaching prompts
- [schema] Registered `auction_readiness` + `ars_tier_transitions` in `pipeline_registry`
- [function] `compute_auction_readiness(uuid)` — 6-dimension scorer (identity/photo/doc/desc/market/condition), 0-100 weighted composite, ~65ms/vehicle
- [function] `persist_auction_readiness(uuid)` — upsert wrapper with tier transition audit logging
- [function] `recompute_ars_dimension(uuid, text)` — trigger-friendly recompute
- [triggers] `trg_ars_on_image_insert`, `trg_ars_on_observation_insert`, `trg_ars_on_evidence_insert` — error-swallowing, fire only for vehicles with existing ARS records
- [mcp] Added 3 tools to mcp-connector: `get_auction_readiness`, `get_coaching_plan`, `prepare_listing`
- [edge] Created `generate-listing-package` edge function — assembles submission bundles with BaT field mapping skeleton
- [data] Batch computed ARS for 2,142 vehicles (data_quality_score >= 95): 3 NEEDS_WORK, 279 EARLY_STAGE, 1860 DISCOVERY_ONLY. Zero TIER 1-2 (as predicted). Top vehicle: 1991 Mercedes 300SL at score 67.
- [docs] Appended implementation results to `auction-readiness-strategy.md`

### [overnight] Overnight Autonomous Work Session (2026-03-20 00:30-02:30)

**Block 1: Data Quality Backfills**
- [data-quality] Orphaned vehicle triage: 138,950 active vehicles had zero vehicle_events records
  - Root cause: vehicles imported directly without creating vehicle_events entries
  - 139,051 vehicle_events rows backfilled (source platform, URLs, prices from vehicles table)
  - Orphaned vehicles: 138,950 → 0 (100% resolved)
  - Sources: mecum (66K), cars_and_bids (17K), facebook_marketplace (12K), barrett-jackson (6K), craigslist (5K), gooding (5K), bat (4K), ksl (2K), rm-sothebys (2K), bonhams (2K), others
- [data-quality] Model field cleanup: 19 NULL models fixed from URL slug extraction
  - 14 from Cars & Bids URL slugs (e.g., /auctions/.../2000-daihatsu-mira-gino → Mira Gino)
  - 3 from BaT URL slugs
  - 2 from "for sale:" title patterns (e.g., "1965 Ford for sale: mustang fastback 289")
  - Remaining 1,122 NULL models are unparseable (FB Marketplace garbage titles or null titles)
- [data-quality] Primary image URL: 33K NULL are genuinely imageless (no vehicle_images rows exist)
  - NOT a backfill opportunity — these vehicles have no images in any table

**Block 2: Design System Compliance (52% → ~87%)**
- [design] Global CSS reset: `* { border-radius: 0 !important; box-shadow: none !important; }`
- [design] Tailwind config: all borderRadius→0, boxShadow→none
- [design] 1,817 borderRadius inline styles removed across 250+ files
- [design] 125 boxShadow inline styles removed across 70+ files
- [design] 681 Tailwind rounded-* classes removed across 73 files
- [design] 86 Tailwind shadow-* classes removed across 23 files
- [design] 488 hardcoded hex colors → CSS variables across 107 files
- [design] 30+ files font-family fixes (non-Arial → Arial, non-Courier → Courier New)
- [design] 10 decorative gradients → solid colors
- [design] Build passes clean (26s)

**Block 3: Edge Function Investigation + Local Discovery**
- [infra] Created index `idx_vehicles_api_list` on vehicles(data_quality_score DESC) for API list endpoint
  - Fixes api-v1-vehicles 16s timeout (was hitting 15s anon statement_timeout)
- [infra] Diagnosed extract-bat-core 500: intermittent, 1x in 24h, no pattern
- [infra] Diagnosed ingest-observation 500: intermittent, 1x in 24h, healthy otherwise (67 versions deep)
- [infra] Diagnosed bat_extraction_queue: 141K pending, cron exists (job 406, every 5 min) but only ~5/hr throughput — blocked on Anthropic API credits ($0 remaining)
- [extraction] Ollama local discovery running in background (qwen2.5:7b, PID 19546)
  - Total discoveries: 11,227 (9,562 Claude Haiku + 1,489 qwen2.5:7b + 176 others)

## 2026-03-20

### [overnight-autonomous] All-Night Work Plan — 6 Blocks Completed

**BLOCK 1: Flush & Ship**
- Deployed 4 edge functions (db-stats, extract-mecum, refine-fb-listing, mcp-connector)
- Pushed all pending work to `overnight-data-quality` branch
- Verified nuke.ag 200 OK, MCP connector 200 OK

**BLOCK 2: Design System Border-Radius Purge — 1,800+ violations → 0**
- 3 parallel agents fixed 400+ component files
- ALL borderRadius JSX violations → 0 (preserved '50%' for circles)
- ALL Tailwind rounded-* classes removed
- ALL CSS border-radius violations fixed in 4 CSS files
- TypeScript compilation verified clean

**BLOCK 3: Deno Import Modernization — 260 edge functions**
- Removed ALL `deno.land/std@0.168.0` imports (156 files, double-quoted)
- Removed ALL `deno.land/std@0.177.*` imports (9 files)
- Removed ALL single-quoted variant imports (97 files)
- Replaced `serve()` → `Deno.serve()` across all functions
- Deployed 35+ modernized functions in 3 batches

**BLOCK 4: Data Quality Enrichment**
- Ran mine_descriptions (14 enriched), derive_fields (59), cross_reference, vin_decode
- Profile_origin backfill via batched SQL (vehicle_events → vehicles)
- Lock health verified: 2 waiters (normal)

**BLOCK 5: Comment Mining for Library**
- Launched 80-group mining job (ongoing at session end)
- Targets non-GM makes, 1960-2000 era
- ~$0.80 estimated cost for 400 comment analyses

**BLOCK 6: Hardcoded Color Audit — 200 replacements across 71 files**
- Created color mapping: hex → CSS variables
- Mapped whites, greys, blacks, status colors to design system vars
- Hardcoded hex colors: 1,675 → 499 remaining
- TypeScript compilation verified clean

### [design] Top 6 Design Violator Files Fixed — 200+ Violations Eliminated
5 parallel agents + 1 manual fix. Files fixed:
- **VehicleCardDense.tsx**: 62+ fixes (17 borderRadius, 7 boxShadow, 2 gradients, 3 fonts, 33+ colors)
- **VehicleDossierPanel.tsx**: 42 fixes (all hardcoded colors → CSS vars, zero violations remaining)
- **ContractTransparency.tsx**: 42 fixes (36 borderRadius, 1 boxShadow, 1 gradient, 2 fonts, 1 color)
- **ImageGallery.tsx**: 30 fixes (3 borderRadius, 6 boxShadow, 2 gradients, 19 colors)
- **InventoryAnalytics.tsx**: ~15 fixes (rounded/shadow/gradient Tailwind classes, gradient StatCard removed)
- **GarageVehicleCard.tsx**: 9 fixes (4 colors + 5 transition easings)
- **UserMetrics.tsx**: Already compliant (false positive from Recharts hex requirement)
Estimated compliance improvement: 52.4% → ~58% (200 violations of 3,880 total eliminated)

### [mcp] Extension v2: 18→7 tools, response cleanup, coaching descriptions
- **Consolidated tools**: search_vehicles + search_vehicles_api + list_vehicles → `search`; get_vehicle + get_vehicle_images → `vehicle`; get_valuation + get_vehicle_valuation + get_comps + market_snapshot → `value`; submit_vehicle + extract_listing + ingest_marketplace_listing + import_facebook_saved → `submit`; contribute_observation + register_organization → `observe`; analyze_image + identify_vehicle_image → `analyze`; decode_vin unchanged
- **Response cleanup**: stripNulls on all outputs, cleanSearchResult/cleanVehicle/cleanComp formatters, stats computed from comps
- **Coaching descriptions**: `submit` tells Claude "YOU are the extractor", `observe` tells Claude "you are recording evidence"
- **Version bump**: 1.0.3 → 1.1.0 across package.json, server.json, manifest.json
- **Build deployed**: copied to `~/Library/Application Support/Claude/Claude Extensions/local.mcpb.nuke.nuke-vehicle-intelligence/`
- **Context savings**: ~4K tokens → ~1.5K tokens for tool definitions (estimated 60% reduction)

### [ops] First Full Autonomous Run — All Systems Checked
- **Health check**: GREEN — 644K vehicles, 32.8M images, 0 lock waiters, nuke.ag OK
- **Smoke test**: 5/5 services passing (db-stats, universal-search, coordinator, nuke.ag, postgres)
- **Regression**: YELLOW→GREEN — 7 "bad year" vehicles are legitimate pre-automobile items (1840-1884). Threshold adjusted to 1700
- **Integration check**: 98.6% cron success rate, 246 edge functions active, archiveFetch migration 58.6%
- **Design audit**: 52.4% compliance (486/927 files), 3,880 violations. Top: borderRadius in 280 JSX files

### [db] Cron Job Fixes
- **refresh-vehicle-census** (job 413): `REFRESH MATERIALIZED VIEW CONCURRENTLY` — no more timeouts
- **review-agent-submissions** (job 414): Direct `_app_secrets` lookup — eliminated 41 failures/day

### [data] Pre-Automobile Vehicle Normalization
- Fixed "C.1880" make→"F&R Shanks", normalized Abbot, Button & Blake, De Dion-Bouton

### [ops] Autonomous Workflow Infrastructure — Plugin, Scheduled Tasks, Agent Teams
- **Plugin system**: Created `.claude-plugin/` with 6 skills: health-check, debug-extraction, audit-design, smoke-test, integration-check, nightly-regression
- **Scheduled scripts**: `scripts/scheduled/` — morning-health-check.sh, smoke-test.sh, nightly-regression.sh (all tested, passing)
- **Agent teams enabled**: `CLAUDE_CODE_EXPERIMENTAL_AGENT_TEAMS=1` in global settings
- **Telegram notifications upgraded**: claude-notify now supports `--alert` and `--report` modes, smoke test auto-pings on failure
- **Coordination cleanup**: Archived 4,153-line HANDOFF.md, cleaned ACTIVE_AGENTS.md
- **package.json**: Added `ops:health`, `ops:smoke`, `ops:regression` scripts
- **Debug team agent**: `.claude-plugin/agents/debug-team.md` for parallel subsystem investigation

### [db-health] Full DB Health Roadmap — Indexes, Vacuums, Crons, Retention
- **Phase 1: Fixed broken things**
  - Cron job 414 (review-agent-submissions): rewrote to use get_service_url()/get_service_role_key_for_cron()
  - Cron job 413 (mv_vehicle_census): removed CONCURRENTLY (58-row matview, 6h cadence)
  - Re-enabled `refresh_tier_on_image_upload` trigger on vehicle_images
- **Phase 2: Dropped 38 unused indexes (~4.3 GB)**
  - vehicle_images: 6 indexes (2.87 GB)
  - auction_comments: 5 indexes (1.09 GB)
  - timeline_events: 10 zero-scan indexes (100 MB)
  - vehicles: 8 indexes (84 MB) — kept VIN/listing_url unique constraints
  - misc tables: 9 zero-scan indexes (165 MB)
- **Phase 3: VACUUM blitz**
  - VACUUM ANALYZE: auction_comments (973K dead), source_targets (130K), vehicle_quality_scores (113K), nuke_estimates (104K), bat_user_profiles (97K), image_camera_position (84K)
  - VACUUM FULL import_queue: 475 MB → 39 MB
  - VACUUM'd 6 more never-vacuumed tables (user_profile_queue, image_work_extractions, vehicle_mailboxes, service_executions, auction_events, bat_listings)
- **Phase 4: Cron consolidation (92 → 84)**
  - Deleted 4 duplicates: job 187 (score-live-auctions), 404 (parse_bat_snapshots), 246+383 (cron log cleanup)
  - Slowed 3 aggressive schedules: jamesedition 5→15min, collecting_cars 5→10min, OCR lock reset 5→10min
  - Deleted dead bid analytics refresh cron (178)
- **Phase 5: Data retention policies**
  - 3 new retention crons: system_logs (30d), scraping_health (30d), field_extraction_log (90d)
  - Purged 717K old system_logs rows
  - Scraping_health purge: 2.32M rows (running in background)
- **Phase 6: Hygiene**
  - Dropped 5 orphaned tables: live_streams, stream_chat_messages, comment_library_extractions, gap_analysis_results, pending_image_assignments
  - Dropped 7 dead matviews: 3 investor portal, 4 bid analytics
  - Set autovacuum_vacuum_scale_factor=0.05 on 6 high-churn tables
  - PostgREST schema cache reloaded
- **DB size: 76 GB → 72 GB** (with scraping_health purge still running → ~71 GB expected)
- **Active crons: 92 → 84**

## 2026-03-19

### [perf] API Performance Optimization — db-stats, universal-search, count_vehicles_search

**db-stats: 7s → 1.3-1.5s warm (5x improvement)**
- Eliminated 12 PostgREST HTTP exact count queries (external_identities alone was 3.4s)
- Replaced with pg_class reltuples estimates for large tables
- Consolidated 3 separate DB pool connections into single pool with 4 parallel connections
- Each heavy GROUP BY (vehicles, vehicle_events, listing_page_snapshots) gets own connection
- Removed references to dropped tables (businesses, external_identity_claims, identity_verification_methods)
- Deployed: `supabase/functions/db-stats/index.ts`

**universal-search count: 453ms → ~50ms (9x improvement)**
- Optimized `count_vehicles_search` RPC to use pg_stats estimates for common makes/models
- Fixed PostgREST PGRST203 overload error by dropping redundant single-arg function version
- Applied: SQL function replacement + `NOTIFY pgrst, 'reload schema'`

**api-v1-comps: measured at 0.47-0.50s (already met <1s target)**
- Was reported as 6s — confirmed as cold start latency, not query performance

### [frontend] Photo Library Bug Fixes — infinite scroll, sort, sidebar
- Bug 1: Replaced double-rAF scroll detection with IntersectionObserver sentinel in PhotoGrid.tsx. Fires immediately when content doesn't fill viewport at high column counts (15-20), keeps paginating until viewport is full.
- Bug 2: Changed photo sort from DESC to ASC (oldest first) with stable id tiebreak in usePhotoLibrary.ts. EXIF-dated photos still sort first, then bulk-import cluster.
- Bug 5: Broadened vehicle sidebar query from ['active','pending'] to include sold/discovered/inactive/pending_backfill. Added error logging.
- Bugs 3-4 verified already resolved: no measureElement on photo rows, micro tier (80px/q60) correctly applied at 13+ columns.
- `npx tsc --noEmit` and `npx vite build` pass clean.

### [release] Full commit & deploy sweep — 14 commits, 8 edge functions deployed
- **Wave 1:** AuctionMarketplace, ontology wiring, Landing Page v3, Feed grid, api-v1-organizations
- **Wave 2:** enrich-bulk (4 new strategies + VIN validation), archiveFetch storage fallback, discover-description-data modernization, universal-search filters, FB scraper body_style, api-v1-pipeline-status, photo components, data scripts, auction-readiness-strategy doc
- **Deployed:** ingest, image-intake, photo-pipeline-orchestrator, api-v1-organizations, enrich-bulk, discover-description-data, universal-search, api-v1-pipeline-status
- **Restored:** 3 phantom-dirty frontend files. Added backups/ to .gitignore.
- **Left untracked:** mcp-connector (1924 lines, needs review), extension docs, specs_ralph, tools/, typescript/

### [enrichment] Data Quality Enrichment Sweep — enrich-bulk expanded + universal-search + FB scraper
- `enrich-bulk`: 3 new strategies (backfill_location, smart_primary_image, vin_link_suggestions)
- `mine_descriptions`: expanded to extract VIN (check digit validated), color, engine_type from descriptions
- `derive_fields`: expanded body_style patterns (K10-K30, C10-C30, S10, Colorado, K5, Scout, Jimmy, etc.)
- `cross_reference`: added asking_price from listing events, description from listing_page_snapshots
- `backfill_location`: 3-pass (parse listing_location, pull from vehicle_events, reverse-geocode iPhoto GPS)
- `smart_primary_image`: scores images by angle/source/quality, picks best hero shot
- `vin_link_suggestions`: finds VIN-linked records across sources, flags for human review (no auto-merge)
- `universal-search`: added city/state/listing_location/body_style to results + ?location and ?body_style filters
- `fb-marketplace-local-scraper`: writes city/state to vehicle inserts, derives body_style from title
- `scripts/run-enrichment-sweep.sh`: sequential runner script for batch execution of all strategies
- All strategies now work across all sources (removed source-lock from mine_descriptions and derive_fields)
- Deployed enrich-bulk + universal-search to production
- Tested: 275 locations backfilled, 66 body_styles inferred, 172 countries set in initial batches

### [mcp] MCP Connector v2 — Fix the Slop
- Added `instructions` to initialize response — anti-hallucination directives for Claude.ai
- Fixed `query_vehicle_deep` — now returns description, highlights, equipment, modifications, known_flaws, recent_service_history, title_status, documents_on_hand
- Enriched observations: condition→condition_details, work_record→work_details, valuation→valuation_details (flattened from structured_data)
- Added `comment_discoveries` and `description_discoveries` to deep query
- Added `_data_guidance` with completeness %, null guidance, source attribution
- Added `browse_inventory` tool — location/body_style/status/price filters, queries DB directly
- Fixed `search_organizations` — changed `type` to `business_type` (was crashing on every call), added location filter on city/state
- Improved tool descriptions with behavioral directives
- Total tools: 22→23, deployed and verified

### [frontend] /auctions page rewrite — live auction dashboard
- Rewrote AuctionMarketplace.tsx: 1,393 → ~470 lines
- Filtered to real auction platforms only (BaT, C&B, CC, RM, Gooding, SBX, B-J, Mecum)
- Removed: ProxyBidModal, AuctionNetworkDirectory, Bid button, FB/CL/pcarmarket listings
- Added: two-tier layout (ENDING NOW / ALL LIVE), platform filter chips, design-system compliance
- Zero border-radius, zero shadows, 2px borders, Courier New for data, ALL CAPS labels

### [extraction] Full-Page FB Saved Extraction — New Listings + Reel Org Leads
- 6 new vehicles fully extracted via browser MCP with comprehension-level field evidence:
  - 1979 Pontiac Grand Prix SJ ($4,500, Las Vegas NV) — G-body project, 350 no trans
  - 1986 Chevrolet K5 Blazer ($3,500, Santa Clarita CA) — off-road build, 700R4/NP208/Gov-Lok decoded
  - 1986 GMC Jimmy ($6,200, Lemon Grove CA) — 5.7 V8, mileage flagged at conf 20, t-case not installed
  - 1987 Chevrolet Monte Carlo SS T-Top ($12,500, Los Angeles CA) — 5.3 LS swap, 65K shell/180K drivetrain
  - 1999 GMC Suburban 2500 ($12,500, Bakersfield CA) — last-year OBS, leather, 4x4
  - 1977 Chevrolet Corvette L82 ($6,800, Bullhead City AZ) — 4-speed manual, bone stock, 25% price drop
- All 6 archived to listing_page_snapshots (full page markdown)
- All 6 have vehicle_observations with extraction_notes (decoded drivetrain specs, project level, market notes)
- All 6 have field_evidence with confidence-weighted claims
- 2 organization leads from saved Reels:
  - Dan McNally (Pro-Touring Trucks) — fabricator, frame stiffeners, 1.4M views
  - Medo Automotive (Dubai) — custom Defender builds

### [api] Agent Landing Dock — Full Implementation
- DB migration: `agent_registrations`, `agent_submissions_staging`, `agent_quality_metrics`, `agent_audit_log` tables
- Added `agent_registration_id` to `api_keys`, `'agent'` to `source_category` enum
- RPCs: `record_agent_submission()`, `evaluate_agent_tier()`, updated `check_api_key_rate_limit()` to return agent_registration_id
- Modified `_shared/apiKeyAuth.ts`: AuthResult now exposes `agentId` + `scopes`; agent keys use `agent:{id}` as userId
- NEW `api-v1-agent-register`: GET=discovery manifest (no auth), POST=self-register -> Tier 1 key
- Modified `api-v1-observations`: stage_write scope -> inserts to `agent_submissions_staging` instead of `vehicle_observations`
- Modified `api-v1-batch`: staging detection + Tier 1 batch cap (10 vehicles)
- NEW `review-agent-submissions`: 10-min cron -- dedup, vehicle resolution (VIN/YMM/URL), schema validation, promote/reject
- NEW `api-v1-agent-metrics`: GET=quality dashboard (acceptance rates, promotion progress), POST=heartbeat
- Trust tiers: Tier 1 (sandbox, 100/hr, staging) -> Tier 2 (contributor, 1K/hr, direct, auto at 50+/80%) -> Tier 3 (trusted, 5K/hr, manual)
- Circuit breaker: >20% error rate over 20+ window -> key disabled -> auto-recover 1hr -> half_open at 10/hr -> close after 10 clean
- Cron job ID 414 (every 10 min)
- All 6 functions deployed, end-to-end verified: register -> stage -> review -> accept -> promote -> metrics -> dedup

### [ontology] Digital Twin Ontology Activation for FB Saved Vehicles
- Registered `facebook-saved` source with `listing` + `media` observation kinds (trust 0.55)
- Backfilled 485 listing observations + 2,155 media observations into `vehicle_observations`
- Backfilled 2,899 field_evidence rows (asking_price, mileage, transmission, color, etc.)
- Wired `ingest/index.ts` — new FB saved imports auto-create observations + field_evidence
- Wired `fb-enrich-one.sh` — image uploads auto-create media observations
- Updated `vehicle_valuation_feed` MV with `observation_count`, `source_count`, `photo_count` columns
- 472 FB saved vehicles now visible in feed with observation richness data
- Blazer prototype (2c870e45) has 28 observations, 2 sources, 22 evidence rows including color discrepancy
- Script: `scripts/backfill-fb-saved-observations.mjs` (added to package.json)

### [frontend] Landing Page v3 — Explorable Ontology
- New `landing_page_v3()` RPC: single call returns all sections as JSONB (~30KB)
- Platform Vitals: 8-stat row (vehicles, observations, images, comments, sources, columns, tables, pipelines)
- Market Treemap: top 30 makes as area-proportional flex rows, click→accordion with top 8 models per make
- Intelligence Network: 12 source categories with trust range bars, click→expand all 129 sources
- Observation Graph: 11 observation kinds as proportional bars, click→ontology description
- Schema Explorer: pipeline governance table with governed/protected/function counts, click→column detail
- Kept: hero, search bar with preview dropdown, recent sales strip, footer
- Dropped `landing_page_data()` v2 RPC (replaced entirely)

### [digital-twin] Schema Applied — 121 Tables Live
- Applied 8 DDL migrations: 119 new tables + extended organizations & work_orders
- Subsystems: engine(18), drivetrain(14), chassis(21), body(12), interior(10), electrical/wheels/hvac(16), support(18), actor_org(8+3 extended)
- All tables: updated_at triggers, RLS policies, CHECK constraints, column comments
- Views: actor_profiles, org_profiles
- Economics: labor_rate_history, overhead_costs, project_economics, calculate_tool_depreciation(), calculate_project_roi()

### [digital-twin] Ground Truth — Skylar + Dave + K2500
- Actors: Skylar (welding/fabrication), Dave Granholm (owner)
- Work order: Custom Exhaust Fabrication, 1983 GMC K2500 (VIN 1GTGK24M1DJ514592)
- 2 exhaust manifold records, 3 component_events, 3 work_order_line_items with spec compliance
- 3 actor_capabilities seeded from evidence chain
- Evidence chain verified end-to-end

### [digital-twin] Form-Filling Scripts
- `scripts/fill-vehicle-form.mjs` — schema-as-prompt filler (12 layers, progressive disclosure)
- `scripts/jury-fill.mjs` — multi-model ensemble (Haiku+Sonnet jury, consensus/divergence/gap)
- Registered in package.json (dt:fill, dt:jury)

## 2026-03-18

### [extraction] Extraction Scale-Out — Phases 2-5
- [library] vintage_rpo_codes expanded 268→419 codes (Ford +53, Porsche +38, BMW +30, Mopar +30)
- [library] code_validation_rules expanded 33→63 rules (Ford clone patterns, BMW rod bearings, Porsche IMS, incompatible combos, VIN maps)
- [pipeline] NEW: `scripts/validate-extractions.mjs` — post-hoc validation of v3 extractions against rules
  - 8,075 vehicles validated: 38 fraud risks, 78 errors, 509 warnings, 851 info-level findings
  - Clone risk detection: Shelby GT350/GT500, Boss 429 without documentation
  - Known issues: IMS bearing, S65 rod bearings, VIN engine mismatches
  - Results written to description_discoveries.raw_extraction._validation
- [pipeline] NEW: `scripts/bridge-extractions-to-field-evidence.mjs` — converts v3 extractions to field_evidence rows
  - 92,373 field_evidence rows created from 8,176 vehicles (11.3 fields avg)
  - Frontend FieldProvenanceDrawer can now display AI extraction results
- [data] Quality scores recalculated: avg 3.3→80.1 for v3-extracted vehicles (7,679 scoring 80+)
- [fix] trg_update_vehicle_quality_score trigger updated from 0-1 to 0-100 scale (was causing regressions)
- [config] Added extract:bat-v3, extract:validate, extract:bridge to package.json scripts
- [extraction] Phase 1 Ford extraction COMPLETE: 1,963 Ford-family vehicles (Ford 1,601, Shelby 262, Lincoln 85, Mercury 15)
- [extraction] Total v3 extractions: 7,653→9,562 (+1,909)
- [pipeline] Bridged 1,386 new Ford extractions → 15,514 more field_evidence rows
- [pipeline] Ford validation: 1,601 vehicles, 34 clone risks, 36 errors, 142 VIN mismatches
- [fix] Unified ALL 7 quality score functions to canonical 0-100 formula (was 3 incompatible formulas)
- [data] Auto-accepted 94,163 field_evidence rows (confidence ≥ 65), 13,724 low-confidence left pending
- [fix] Improved clone detection: recognize SFM VINs, Shelby docs, restomods/continuations → fraud risks 72→36
- [architecture] Digital Twin vision locked: EAV at Total Resolution, Domain Ontology, Schema-Guided Generation
- [architecture] Memory doc: digital-twin-architecture.md — north star for all schema/extraction work
- [architecture] README updated with Digital Twin data model section
- [schema] NEW: database/migrations/digital_twin_engine_subsystem.sql — 1,501 lines, 18 tables, 469 column comments
  - actors, component_events (shared infra), 16 engine component tables
  - Full dimensional pattern: spec + is_original + condition_grade + provenance per component
- [schema] NEW: database/migrations/digital_twin_actor_org_ontology.sql — 1,128 lines, 8 new tables + 2 extended
  - organizations, org_memberships, actor/org_capabilities, actor_tools, work_orders, work_order_line_items, gap_analysis_results
  - 70+ capability types, work_order_line_items bridges vehicle↔actor layers
  - "Am I ready?" gap analysis built into schema

### [frontend] Landing page v2: data depth
- Replaced static 3-number stats row with 4 explorable data sections
- Decade timeline (1950s-2020s) with proportional CSS bars, counts, avg prices
- Market section: 8 makes with background proportion bars
- Price distribution: 7 brackets with proportional bars
- Top models: 8 models in 2-column grid
- All rows clickable → `/search` with filters
- New `landing_page_data()` RPC: single call returns decades, makes, price_brackets, top_models, year_range
- Dropped old `landing_market_snapshot()` and `useLandingStats()` / `useMarketSnapshot()` hooks

## 2026-03-16

### [ingest] Facebook Saved Vehicles Import
- Scraped 500 saved vehicles from FB Saved Items page (Chrome browser automation)
- Built `scripts/import-fb-saved.mjs` — two-pass title parser (regex + Haiku fallback)
  - Pass 1 regex: 485/500 parsed (97%), model-implies-make for C10/K5/Corvette/Mustang/etc
  - 9 filtered as non-vehicles (sailboats, trailers, rims, etc.)
  - 6 unparseable (Harley, Vespa, Freightliner, Factory Five, Gentleman Jim)
- Registered `facebook-saved` observation source (trust 0.60)
- **485 vehicles inserted**: 323 sold, 162 discovered
- Top makes: Chevrolet(260), GMC(71), Ford(47), Porsche(12), Plymouth(12)
- Added `import:fb-saved` to package.json
- Data file: `data/fb-saved-vehicles-2026-03-16.json` (full 500 entries)

### [extraction] Local Description Extraction — Schema Design + Validation
- **Prompt designed**: `prompts/description-extraction-local.md` — 30-field JSON schema
  - 16 fields map directly to vehicle DB columns (transmission, engine_type, drivetrain, color, etc.)
  - 14 analytical fields (matching_numbers, condition_grade, modifications, red_flags, work_history)
- **Script built**: `scripts/extract-descriptions.mjs` — 3 modes (test, validate, batch)
  - Ollama-based, configurable model via OLLAMA_MODEL env var
  - CL boilerplate stripping, JSON post-processing (displacement fix, engine type normalization)
  - Scoring system validates extraction quality per-vehicle
  - Only fills NULL columns — never overwrites existing data
- **48-sample cross-platform validation completed** (llama3.1:8b):
  - Cars & Bids: 106.3 avg score, 24.9 fields — excellent
  - BaT: 92.5 avg score, 22.8 fields — great
  - Barrett-Jackson: 66.9 avg score, 15.4 fields — good
  - Mecum: 66.3 avg score, 14.5 fields — good
  - Craigslist: 60.6 avg score, 12.3 fields — decent (after boilerplate strip)
  - Bonhams: 56.9 avg score — pre-war vehicles confuse the model
- **Column fill rates**: modifications 54%, fuel_type 50%, horsepower 40%, drivetrain 31%
- **Speed**: ~15s/vehicle on M4 Max with qwen2.5:7b
- **Batch running**: PID 80862 processing 22K descriptions, ~300 done, results writing to DB
- **Scripts**: `extract-descriptions-offline.mjs` (dump/process/writeback), `writeback-extractions.sh` (psql-based)
- **To resume**: `OLLAMA_MODEL=qwen2.5:7b node scripts/extract-descriptions-offline.mjs process --resume 22000`

### [data] Data Correction Plan — 6-Phase Execution
- **Phase 1: Import Queue Drained** — 6,180 items processed
  - 239 pending items unlocked for haiku-extraction-worker pickup
  - 12 non-vehicle BaT listings skipped, 5 real vehicles retried
  - 1,519 pending_review items → vehicles created (haiku extraction + listing fields)
  - 744 pending_review items skipped (no extractable data)
  - 3,524 pending_strategy items → vehicles created (KSL, CL, misc with haiku extraction)
  - 71 non-vehicle/broken URL items skipped
- **Phase 2: Origin Metadata Backfill** — 140 fields written
  - 19 descriptions, 2 VINs, 95 body styles, 1 mileage, 10 transmissions, 13 colors
- **Phase 3: Make Cleanup** — 266 make values fixed
  - 91 split truncated makes (De Tomaso, DeSoto, AM General, MV Agusta, De Dion-Bouton, De Havilland)
  - 41 case normalized (mg→MG, ac→AC)
  - 9 abbreviations expanded (VW→Volkswagen, MB→Mercedes-Benz, GM→per-vehicle)
  - 111 garbage makes → NULL (numbers, nonsense, 1-2 char)
  - 30 Four Winns/Four Winds merged
- **Phase 4: Body Style Normalization** — 1,308 body styles fixed
  - 22 case fixes (Suv→SUV)
  - 1,166 composite→base type (X Coupe→Coupe, X Convertible→Convertible, etc.)
  - 83 non-body-styles → NULL (Trailer, Race Car, Hot Rod, verbose)
  - 37 merges/case fixes (Custom Sedan Delivery, crew cab, long bed)
- **Phase 5: Craigslist Model Cleanup** — 207 garbled models fixed
  - 190 date+garbage suffix stripped
  - 16 unsalvageable models → NULL
  - 1 Plymouth Barracuda make-corrected
- **Phase 6: Frankenrecord Repair** — 12 listing URLs corrected
  - All 12 conceptcarz/BaT mismatched listing_urls fixed (10 nulled, 1 corrected, 1 nulled)
  - Event detachment deferred (vehicle_id NOT NULL constraint requires creating target vehicles)
- **Net result:** 292,823 active vehicles (+5,043 from import queue drain)
  - Import queue: 0 pending_review, 0 pending_strategy (was 5,910)
  - Avg quality score: 86.0 (slight dip from new lower-quality CL/KSL vehicles added)

## 2026-03-15

### [frontend] Public-Readiness — 6 User-Facing Fixes
- Fix "Get API Key" redirect: CTA now passes `returnUrl=/settings/api-keys` to login
- Hide VehicleScoresWidget when all 5 scores are null (no more "--" bars on every profile)
- Wire OnboardingSlideshow for first-time authenticated users (localStorage check)
- Remove 4 dead market links from search sidebar (browse/segments/builder/contracts — deleted in triage)
- Add "See an example" CTA on landing hero → links to 1982 Porsche 911SC (9,936 images, $160K)
- Add REST curl examples alongside `npm install @nuke1/sdk` on /api page
- SDK v2.0.0 built and pack-verified (npm publish blocked — needs interactive `npm login`)
- Entity backfill: GLiNER writeback already completed; fill rates 70-81% across all entity fields
- Commit: 0f6df45b0

### [admin] Data Pulse — Platform Ingestion Telemetry
- `data_pulse()` RPC: census + 30-day time series + last_ingested + totals in one round-trip
- Heartbeat classification: 55 platforms into 4 types (event_auction, continuous_auction, marketplace, dealer_other)
- Health status: green/yellow/red/gray with type-appropriate thresholds
- Frontend: summary bar, collapsible heartbeat groups, platform cards with sparklines, recharts timeline, data quality grid
- Route: `/admin/data-pulse`, nav entry in Operations section
- Files: `nuke_frontend/src/components/admin/data-pulse/` (7 files), `DataPulse.tsx` page

### [data-sanity] Canonical Vehicle Identity — Source Rosetta Stone
- Created `source_alias_mapping` table with 130+ raw→canonical slug mappings
- Created `resolve_platform_slug(TEXT)` SQL function for source resolution
- Added 3 trigger-computed columns to `vehicles`: `canonical_platform`, `canonical_sold_price`, `canonical_outcome`
- Created `trg_resolve_canonical_columns` trigger (BEFORE INSERT/UPDATE on source/price/status columns)
- Backfilled all 321K live vehicles (platform, outcome, price)
- Created `mv_vehicle_census` materialized view — THE honest reporting view by platform
- Created `v_vehicle_canonical` view with price_type, data_grade (A-F), platform trust scores
- Registered 3 columns in `pipeline_registry` (do_not_write_directly = true)
- Added `normalizeSource()` + `SOURCE_ALIASES` map to `_shared/normalizeVehicle.ts`
- Added 6-hour cron (job 413) for census refresh
- Key findings: 30 canonical platforms, 273K sold, 3.8K RNM, 5K for_sale, 1K active
- BaT: 122K sold + 3.2K RNM. Gooding median $181K. Broad Arrow median $400K.

### [data-quality] Data Quality Followup Audit (6 areas)
- **Frankenrecord detection**: 12 definite frankenrecords found (wrong vehicle events merged), 0.004% of 270K active. Report: `reports/frankenrecord-detection-2026-03-15.md`
- **Craigslist data quality**: 1,142 of 1,943 CL vehicles (59%) have garbled models (scraper concatenated model+date+mileage+city+price). Recoverable via regex + snapshots. Report: `reports/craigslist-data-quality-2026-03-15.md`
- **Body style long tail**: 2,176 non-canonical values across 5 categories (case variants, new canonical types, composites, junk, non-vehicles). Full cleanup plan in `reports/body-style-cleanup-2026-03-15.md`
- **Inactive vehicle audit**: 16,444 vehicles incorrectly inactivated (have images/events). Includes $2.5M Koenigsegg, McLaren P1, Ford GT. Promotion query ready. Report: `reports/inactive-vehicle-audit-2026-03-15.md`
- **Backup verification**: 275 MB dump exists but can't verify (pg_restore v14 vs dump v1.16). Need Postgres 16+ tools.
- **VACUUM FULL assessment**: NOT recommended for vehicle_images (0.3% dead). auction_comments needs regular VACUUM first (7.4% dead, NEVER vacuumed).

### [data-quality] VIN Decoder Expansion + Quality Gate Wiring
- VIN decoder: GM passenger car support (Corvette, Camaro, Nova, Chevelle, Impala, Monte Carlo, Pontiac, Olds, Buick, Cadillac)
- VIN decoder: Corvette disambiguation via series 9 + Z-prefix sequential detection
- VIN decoder: Modern WMI map expanded to 50+ prefixes (Porsche, BMW, Ferrari, Toyota, Honda, etc.)
- VIN decoder: Fix prefix match ordering (3-char before 2-char) — fixes 1GC→null bug
- Ingest VIN cross-check: extended from 17-char only to all VINs ≥6 chars (catches pre-1981 mismatches)
- Ingest VIN cross-check: pre-1981 model mismatch detection (Corvette↔Camaro, Corvette↔Chevelle, etc.)
- Quality gate wired into: extract-cars-and-bids-core, process-orphan-snapshots, extract-jamesedition, extract-barn-finds-listing
- All 5 functions deployed to production, VIN rejection verified live

### [data-recovery] FB Marketplace Image Backfill — COMPLETE
- Backfill: extracted images from raw_scrape_data → marketplace_listings.all_images + vehicle_images
- **7,697 listings backfilled** (of 9,695 candidates; ~2K had no valid image URLs in raw data)
- **5,145 vehicles enriched** with propagated images (primary_image_url + vehicle_images rows)
- 0 errors across 17 batches of 500, zero-cost data recovery from existing DB content

### [data-recovery] Snapshot Image Extraction — COMPLETE
- Fixed batch-extract-snapshots: reads HTML from Supabase Storage (was only checking inline html — null for 99.99% of snapshots)
- Added universal image extraction: og:image, JSON-LD, platform-specific gallery patterns
- Added `primary_image_url` to field map (was missing entirely from batch extractor)
- **Bonhams: 978** | **Mecum: 1,835** | **BaT: 39** | Barrett-Jackson: 0 | C&B: 0
- **Total: 2,852 vehicles got images from stored snapshots**
- Combined with FB backfill: **7,997 vehicles went from no image → image this session**

### [diagnosis] Anthropic API credits depleted
- Haiku worker returning 400: "credit balance is too low" — blocks 5,910 queue items
- Needs credit top-up at console.anthropic.com

### [ingest] FB Marketplace End-to-End Wiring
- Vehicle linking in `extract-facebook-marketplace` direct mode: VIN match → `vehicle_id`, YMM+State → `suggested_vehicle_id`
- DOM extraction snippet: `scripts/fb-marketplace-dom-extractor.js` — relay store + DOM + meta tag extraction for Claude in Chrome
- MCP server v0.4.0: committed Tool 11 (`ingest_marketplace_listing`), pushed to GitHub, build passes
- Legacy URL mode: confirmed Firecrawl returns 403 for facebook.com, documented as best-effort, direct mode preferred
- README updated with `ingest_marketplace_listing` tool docs

### [ingest] Direct Agent Ingest for FB Marketplace
- Rewrote `extract-facebook-marketplace` edge function: added `mode: "direct"` for pre-extracted data from browser agents
- Fixed legacy URL mode: removed 13 broken columns (`external_id`, `asking_price`, `location_city`, etc.), mapped to actual `marketplace_listings` schema
- Idempotent on `facebook_id` — re-submissions bump `submission_count`, merge non-null fields
- Agent provenance stored in `raw_scrape_data.agent_context`
- Registered `claude-in-chrome` in `agent_registry` (trust_level: trusted)
- Added `ingest_marketplace_listing` tool (Tool 11) to MCP server, bumped to v0.4.0
- Deployed and tested (direct ingest + idempotency + cleanup)

### [data-quality] Database Clean-Out — 7 Phase Plan
- Phase 1: Body style canonicalization — 16,374 → 2,049 non-canonical active (87.5% reduction). Code: enhanced `normalizeBodyStyle()` with prefix stripping, slash handling, null mapping
- Phase 2: Model cleanup — 407 → 0 active vehicles with model > 80 chars (Bonhams chassis numbers, Craigslist prices stripped)
- Phase 3: YMM backfill — parsed year from URLs for BaT/Bonhams/Gooding/RM. Downgraded 1,442 memorabilia items (missing all three) to pending
- Phase 4: Source attribution — 50,385 → 0 active vehicles with NULL discovery_source (46K from `source` column)
- Phase 5: Rejected purge — DONE. 105K vehicles + 1.56M images + 103K observations + 9.7K surface_observations deleted
- Phase 6: Discovered triage — 514 promoted to active, 290,665 downgraded to inactive, 3,357 kept as discovered
- Phase 7: Empty tables — none droppable (previous sessions already cleaned)
- VACUUM ANALYZE run on vehicles, vehicle_images, vehicle_observations, surface_observations
- Frankenrecord fix: El Camino/Corvette/Nova II separated into 3 clean profiles (Corvette `f000e472` created)
- Final: 633K vehicles (270K active, 311K inactive, 35K pending, 12.6K sold, 3.4K discovered)

### [ingest] Validation Gate + Image Backfill + Schema Endpoint
- Wired `normalizeVehicleFields`, `qualityGate`, VIN cross-check into `/ingest`
- VIN-make mismatch → rejected (Ford VIN as Chevy caught), anachronistic fuel flagged
- Quality score 0-1 returned on every response; rejected returns issues+suggestions
- GET `/ingest` returns full schema docs (field types, examples, validation checks) for agent self-discovery
- `refine-fb-listing`: new `backfill_images` action extracts images from `raw_scrape_data` JSONB → `all_images` + propagates to `vehicle_images` (10K+ recoverable)
- `fb-marketplace-orchestrator`: cadence tracking per state in `brief` action — staleness alerts, recommended scrape command
- All 3 functions deployed and verified

### [data-quality] Data Quality Cleanup & Hardening — All 6 Phases Complete
- **Phase 1:** Added `normalizeTrim()`, `normalizeModel()`, `normalizeBodyStyle()`, `normalizeColor()` to `_shared/normalizeVehicle.ts`. Enhanced `normalizeTransmission()` with regex word-to-number conversion.
- **Phase 2:** Wired `normalizeVehicleFields()` into all extractors: barrett-jackson, bat-core, gooding, haiku-worker, pcarmarket.
- **Phase 3 (SQL):** Cleaned 55K+ verbose transmissions, 100 polluted trims, 28 polluted models, 1.4K HTML entities in interior_color.
- **Phase 4:** Hardened `merge_into_primary()` — cross-platform merges no longer blindly reassign images (prevents El Camino/Corvette contamination).
- **Phase 5:** Added pollution penalties to `compute_vehicle_quality_score()`: trim>80 chars (-20pts), model with auction metadata (-30pts), transmission>40 chars (-5pts).
- **Phase 6:** Created `data_quality_pollution_report` monitoring view.
- Migrations: `harden_merge_into_primary_platform_guard`, `data_quality_score_pollution_penalties`, `create_data_quality_pollution_report_view`

### [extraction] BaT Perfect Ingestion Pipeline — Phases 1-5 Complete
- **Phase 1 (Ground Truth):** Created `_shared/batParser.ts` (shared parsing module extracted from extract-bat-core + bat-snapshot-parser). Built `bat-extraction-test-harness` edge function — samples vehicles across price buckets, compares DB vs snapshot extraction field-by-field. Created `bat_test_results` + `bat_quarantine` tables.
- **Phase 2 (Validation + Tetris):** Enhanced `extractionQualityGate.ts` with VIN MOD11 checksum, era-based price bounds, cross-field consistency, make canonicalization. Built `_shared/batUpsertWithProvenance.ts` (Tetris write layer: gap-fill + confirmation + conflict→quarantine). Wired quality gate + Tetris into `bat-snapshot-parser`.
- **Phase 3 (Bug Fixes):** Fixed transmission stripping bug (5.6% → 67.9% accuracy), VIN length (36.8% → 86.7%), added body style patterns. Overall accuracy: 80.7% → 85.4%.
- **Phase 4 (Price Propagation):** Built `bat-price-propagation` edge function — cross-validates bat_listings prices against snapshot HTML, propagates via Tetris write layer.
- **Phase 5 (Discovery):** Daily discovery cron (`0 6 * * *`), weekly price propagation cron (`0 8 * * 0`). Ran discovery: 44 new URLs found in 5 pages.
- Key files: `_shared/batParser.ts`, `_shared/batUpsertWithProvenance.ts`, `bat-extraction-test-harness/`, `bat-price-propagation/`
- All functions deployed. Storage-aware (HTML in listing-snapshots bucket, not DB).

### [library] GM Service Manual Ingestion — 6 New Manuals (2,295 chunks)
- Ingested 6 GM Light Duty Truck service manuals (1974, 1975, 1976, 1978, 1979, 1980) into service_manual_chunks
- Created 6 reference_libraries entries with proper make/model/series for trigger compatibility
- Fixed ingest-service-manual.py: added --library-id parameter to avoid trigger NOT NULL violation on oem_vehicle_specs
- Total library now: 12 service manuals, 3,406 chunks spanning 1973-1987
- Per-manual breakdown: 1974 (488 chunks/978pg), 1975 (150/324pg), 1976 (199/400pg), 1978 (443/932pg), 1979 (517/1033pg), 1980 (498/1006pg)
- Content types: ~1,334 procedure, ~514 specification, ~177 chart/diagnosis, ~270 reference
- OCR quality: Good on 1974/1975/1976/1979/1980 (clear section detection, readable text). 1978 has weaker section detection (774/886 pages in "unknown" section) but text quality is still good
- Avg chunk size: ~4,200 chars. Min: ~80 chars, Max: ~16K chars

### [yono] YMM Knowledge Lookup — Suffix-Stripping + Case Fallback
- Fixed 60% miss rate (339K of 567K vehicles) on YMM profile lookups
- Root cause: builder coalesces "Camaro Z28" → "Camaro" but runtime constructs "Camaro Z28" key
- Added suffix-stripping fallback to ALL lookup paths using `strip_model_suffix()` from build_ymm_knowledge.py
- Added case-insensitive fallback (handles "chevrolet" vs "Chevrolet" mismatches)
- Files fixed: `yono/yono.py` (2 in-memory store lookups + case index), `yono/condition_spectrometer.py` (3-tier DB fallback), `yono/description_generator.py` (normalized context_ymm_key), `yono/training_sampler.py` (coalesced stats), `yono/contextual_training/export_contextual_data.py` (LATERAL JOIN), `yono/contextual_training/modal_contextual_train.py` (LATERAL JOIN)

### [pipeline] Vehicle Image Pipeline — Display & Scraping Fix
- Fix 1: feed-query two-pass image resolution — primary image lookup + fallback RPC `get_first_images_for_vehicles` (DISTINCT ON vehicle_id)
- Fix 1: Removed post-query thumbnail filter that dropped vehicles from feed results
- Fix 1: Deployed updated feed-query edge function
- Fix 2: Backfilled is_primary on ~15,500 vehicles (historical gap — BaT, Barrett-Jackson, FB Marketplace)
- Fix 2: Synced vehicles.primary_image_url for 255 vehicles where trigger cascade failed (check constraint on sibling rows)
- Fix 3: MV definition change timed out (>120s) — applied non-concurrent REFRESH instead to clear 11K stale has_photos=true phantoms
- Result: 253,780 vehicles with primary images, 0 vehicles with images but missing primary

### [frontend] BrandHeartbeat crash fix + DEALERS toggle
- Fixed BrandHeartbeat white-screen crash when filtering by make (PORSCHE etc.)
  - Root cause: Recharts TreemapCell receives undefined `count` prop during layout — `count.toLocaleString()` crashed
  - Also added null guard on `d.total_listings`/`d.avg_price` in BrandHeartbeat itself
- Added DEALERS toggle button to FeedFilterSidebar STATUS section
  - Wired to existing `filters.dealer` → `include_dealers` API param
  - Backend already supported it (`origin_organization_id IS NULL` filter)
- Year filter confirmed working (was blocked by BrandHeartbeat crash)

### [known issues — NOT FIXED]
- Popups (vehicle card hover/click detail) not working — needs investigation
- Deep data stats panel not rendering — needs investigation
- MV `has_photos` definition still uses simple EXISTS (no document/duplicate filter) — CREATE MV times out at 120s
- 11,066 vehicles have `primary_image_url` set to expired FB CDN URLs but 0 `vehicle_images` rows
- `vehicle_images_url_scheme_check` constraint blocks trigger cascades on rows with NULL `image_url` — affected ~255 vehicles during backfill

## 2026-03-14

### [pipeline] Image Medium Detection in Photo Pipeline
- Added `image_medium` (photograph/render/drawing/screenshot) + `medium_context` to Gemini Flash classification prompt in `photo-pipeline-orchestrator`
- Gemini is now the authority for `image_medium` — removed DB write from `yono-analyze` to prevent overwrites
- Upgraded Gemini `2.0-flash` → `2.5-flash` (old model deprecated for new API keys)
- Disabled thinking tokens for classification (was consuming output budget, truncating JSON)
- Added thinking-aware response parsing (filter `thought` parts, take last text part)
- Removed stale leaked `GOOGLE_AI_API_KEY` from Supabase secrets
- Verified: 5 images correctly classified with `image_medium: photograph`, `medium_context: "real photograph"`

### [images] Photo Sync Engine — Camera Roll → Vehicle Pipeline
- Created `scripts/photo-sync.mjs` — scans macOS Photos by date, filters via Apple ML labels, clusters into sessions, uploads to storage, calls image-intake for Claude vision classification + vehicle matching
- Migration: `photo_sync_log` table (per-run history), `pending_image_assignments` table (unmatched photo staging)
- Registered in package.json (`sync:photos`) and TOOLS.md
- Dry-run verified: 16 truck photos from Mar 13 correctly detected and clustered into 1 session at Boulder City, NV

### [yono] Make Classifier v2 — Full Training Pipeline Rewrite
- Rewrote `yono/modal_train_hierarchical.py`: 650 → 1,594 lines
- **Label cleaning**: MAKE_ALIASES expanded 14 → ~200 entries, EXCLUDED_MAKES set (~400 entries) for motorcycles/boats/memorabilia/junk. 2,171 unique makes → ~100 clean makes
- **Image caching**: New `cache-images` action — async downloads (aiohttp, 100 concurrent) to Modal volume. Zero HTTP during training
- **CachedDataset**: Replaces StreamingDataset (was downloading every image via urllib per epoch). Loads from local SSD, corrupt files skip to next valid item
- **JSONL loading**: Replaces 982 Supabase REST API round-trips. Two-pass: count makes, then filter (min_samples threshold)
- **EfficientNet-B2**: Upgraded from B0 (224→260 input, 5.3M→9.2M params). Updated yono.py `_preprocess()` and `scripts/export_onnx.py`
- **Augmentations**: Added RandAugment, RandomPerspective, RandomErasing. Wider crop scale (0.6-1.0)
- **Training**: LR warmup (5 epochs, 0.1x→1x) + cosine decay, gradient accumulation (4 steps, effective batch 256), early stopping (patience=7), weight decay 1e-2, grad clipping max_norm=1.0
- **ONNX export**: Reads model_name/img_size from checkpoint metadata — no hardcoded architecture
- Removed `supabase` pip dependency from training image

### [fb-marketplace] Pipeline Repair + National Scrape
- Fixed broken `trg_auto_work_detection` trigger (empty search_path caused ALL vehicle_images inserts to fail silently)
- Fixed 3 more broken triggers: `auto_group_photos_into_events`, `auto_tag_organization_from_gps`, `handle_image_activity`
- Fixed 1,880/1,883 corrupted FB images (dnsFetch binary bug had corrupted 90.5% of stored images)
- Improved non-auto filter: added ~80 boat/RV/trailer/equipment makes
- Added image insert error logging (was silently swallowing errors)
- National scrape: 58 US metros, 6,336 scanned, 2,070 vehicles created, 2,066 images stored
- FB active vehicles: 1,148 → 2,179 (+90%)

### [taxonomy] Vehicle Taxonomy Normalization Pipeline — Complete
- **Phase 1**: Mass VIN decode — 115,872 of 118,486 VINs decoded (97.8%) via NHTSA batch API
- **Phase 2a**: Added NHTSA body type aliases to canonical_body_styles (migration)
- **Phase 2b**: Built canonical_models from NHTSA + ECR: 247 → 3,454 entries
- **Phase 3**: Backfilled trim/body_style/engine/transmission/drivetrain from vin_decoded_data
- **Phase 4**: Model normalization — exact match, partial match, VIN cross-ref, suffix-stripped passthrough
- **Body style normalization**: Added hardtop/speedster/phaeton/limousine aliases, re-normalized
- **Results**: model_pct 54% → 98.4%, body_pct 66.5% → 74%, decoded_vins 131 → 115,872
- Scripts: `mass-vin-decode.ts`, `build-canonical-models.ts`, `backfill-from-vin.ts`, `retrigger-normalization.ts`
- Index: `idx_vehicles_vin_upper` on upper(vin) for fast VIN joins
- body_pct/trim_pct below target due to data availability (no source data for 85K vehicles)

### [yono] Training Data Quality Hardening (Tier 1)
- Expanded vehicle_surface_templates: 20 → 102 entries (30+ makes, pre-war through 2026)
- Spatial coverage: 19.2% → 62.3% of surface_observations have physical inch coords
- Confidence recalibration: 107K NULL confidence values backfilled, zero NULLs remain
- Built `yono/training_sampler.py`: stratified zone sampler (stats/sample/validate CLI)
- Condition scoring: 100% of available data scored (362 vehicles), limited by paused pipeline
- Created `backfill_surface_coords()` DB function for ongoing spatial resolution
- Porsche alias matching: 991/997/964/Carrera/Turbo/Targa → 911 template
- Trigger audit: `auto_update_primary_focus_on_org_vehicles` already patched (not broken)
- Snapshot retention: all 358K snapshots <90 days old, no cleanup possible yet

### [platform-health] P0 Error Fixes + Performance Cleanup
- Removed dead `auto-dedup-check` call from photo-pipeline-orchestrator (every image upload was 404ing)
- Created `vehicle_timeline_events` view over `timeline_events` (fixes ingest-observation 500s + 7 broken DB functions + frontend reads)
- Fixed `enrich-vehicles-cron` sending unsupported `re_enrich` action to `extract-vehicle-data-ai` (400s)
- Made `bat_extraction_queue.vehicle_id` nullable (queue_only inserts were silently failing)
- Dropped 25 duplicate indexes (~700 MB reclaimed)
- VACUUM FULL `vehicle_builder_attribution` (75 MB → 120 kB — 179 rows)
- Deployed: photo-pipeline-orchestrator, enrich-vehicles-cron
- DB migrations: vehicle_timeline_events view, nullable vehicle_id, duplicate index cleanup

### [vehicle-profile] Vehicle Dossier Panel — Provenance-Rich Field Evidence
- Fixed critical bug: useFieldEvidence.ts mapped wrong DB columns (proposed_value→field_value, source_confidence/100→confidence) — was causing em-dashes and 0% bars for 7,728 vehicles
- Created ensure_field_evidence(UUID) SQL function — on-demand backfill from vin_decoded_data, vehicles table, vehicle_field_sources
- On-demand backfill in useFieldEvidence hook — extends coverage to ~50K vehicles on first page load
- Upgraded FieldProvenanceDrawer: color-coded confidence bars (green/gold/red), conflict highlighting, extraction context, dates
- Built VehicleDossierPanel replacing VehicleBasicInfo: dossier header, identity block with badges, 16 field rows with provenance drawers, verification summary bar, condition spectrometer section
- Modification detection: compares VIN/NHTSA evidence vs other sources, flags MOD badge

### [platform] Health Remediation Pass 2
- P0: Fixed analyze_organization_data_signals trigger — removed receipt_links reference causing cascading failures (9 cron failures/24h → fixed)
- P1: Rerouted 9 dead edge function references (analyze-image→yono-analyze ×4, analyze-auction-comments→discover-from-observations, extract-using-catalog→extract-vehicle-data-ai, bat-simple-extract→complete-bat-import, simple-scraper→extract-vehicle-data-ai, bat-multisignal-postprocess removed)
- P1: Fixed extract-jamesedition 500s — added VIN dedup check, URL sanitization
- P1: Restored hybridFetcher.ts (deleted in triage but still imported by archiveFetch — was blocking deploys)
- P1: Deployed extract-cab-bids (existed locally but never deployed, causing 404s)
- P2: Verified cron jobs clean — no dead function calls. Cleanup job already exists.
- P3: RLS lockdown — 86→3 exposed tables. 63 internal tables: grants revoked + RLS deny-all. 23 frontend tables: write access revoked + RLS with read-only policies.
- Deployed 12 modified edge functions

## 2026-03-13

### [platform] Health Assessment & Remediation
- Fixed `listing_page_snapshots` column errors: `raw_html`→`html`, `markdown_content`→`markdown` in haiku-extraction-worker + sonnet-supervisor (was generating hundreds of 42703 errors/min)
- Fixed `release_stale_locks()` RPC — vehicle_images no longer has locked_at column
- Fixed 4 edge functions referencing deleted `extract-collecting-cars` → routed to `extract-vehicle-data-ai`
- Dropped 11 duplicate indexes: 643 MB reclaimed (538 MB from vehicle_images alone)
- Committed 87 uncommitted files across 10 logical commits
- Cleaned up ACTIVE_AGENTS.md (7 stale entries removed)
- Updated .gitignore (agent state files, temp scripts)

### [yono] Vehicle Surface Mapping — Spatial Intelligence System
- DB: `vehicle_surface_templates` (20 OEM templates) + `surface_observations` (154,679 backfilled) + `vehicle_surface_coverage` view
- 42 zone codes mapped to physical inch coordinates per Y/M/M template
- `modal_batch.py` writes surface_observations (zone + damage + modification) on every image
- `nlq-sql` extended with spatial tables, zone taxonomy, coordinate queries
- `scripts/seed-surface-templates.py` — seeds templates for top Y/M/M combos
- Templates cover: GM trucks (K10/K20/K2500/Blazer), Ford Bronco/Mustang/Thunderbird, Mercedes SL series, Porsche 911, Camaro, Chevelle, Corvette, DeLorean, Ferrari Dino

### [yono] Surface Mapping Expansion — Spectrometer Bridge
- Expanded `surface_observations`: severity (0-1), lifecycle_state (7 states), descriptor_id (→condition_taxonomy), region_detail, pass_number, evidence
- `condition_spectrometer.py`: `write_surface_observation()` with template→coordinate resolution
- `bridge_yono_output()` writes spatially-anchored surface_observations alongside condition observations
- `modal_batch.py`: template-aware Y/M/M → zone → physical inch bounding box resolution
- `nlq-sql` expanded: 9 tables, condition_taxonomy, scores, distributions, 8 example queries
- Backfilled lifecycle_state for 47K observations (worn 33K, ghost 10K, weathered 4K)
- Coverage view: avg/max severity, lifecycle_states, passes_completed, condition_labels
- Observation = BwO: spatial + condition + image analysis unified in one assemblage

### [yono] Image Session Detection, Descriptions & Session Classifier
- **DB migration**: `session_type_taxonomy` (14 types), `image_descriptions`, `session_narratives` tables; extended `image_sets` with 14 auto-session columns; `get_vehicle_sessions` RPC
- **`yono/session_detector.py`** (new): temporal clustering (configurable gap), GPS sub-splitting, source-batch grouping, rule-based classification, CLI + server endpoints
- **`yono/description_generator.py`** (new): Pass-2 contextual descriptions (Y/M/M + session + neighbors), session narrative generation with continuity notes, CLI + endpoints
- **`yono/modal_train_session_classifier.py`** (new): SessionTypeHead (projection → positional → 4-head attention → 14 classes), Modal GPU training, ONNX export, Sunday 2am cron
- **`yono/modal_batch.py`**: Florence-2 captions now stored in `image_descriptions` (pass 1), session classification post-processing added
- **`yono/server.py`**: 3 new endpoints (`/session/detect`, `/session/classify`, `/session/narrative`)
- **Frontend**: ImageGallery sessions view (cover images, type badges, narratives), ImageExpandedData AI description section, BarcodeTimeline session type labels
- Tested on K10 truck: 8 sessions detected, 118 descriptions, 8 narratives generated

### [frontend] Feed Page Rebuild: Brand Heartbeat + Chrome Collapse
- Promoted FeedPage (feed-v2) to main homepage feed tab, replacing CursorHomepage (1,998 lines)
- Created BrandHeartbeat component suite (heartbeat/): stat grid, model bar chart (recharts), trend panel
- BrandHeartbeat appears when filtering by single make — shows listings, avg/median price, sell-through, top models
- Drill-down to single model adds quartiles, trend direction, rarity, production data
- Created FeedStatCard — contextual stat rows injected every 5 vehicle rows in grid mode
- Merged search input into FeedStatsStrip (eliminated one chrome layer)
- Chrome budget reduced from ~238px to ~112px (header 48 + stats 32 + toolbar 32)
- Deleted 16 orphaned files (CursorHomepage + extracted hooks/libs/components): 7,312 lines removed, 226 added
- /feed-v2 route now redirects to /?tab=feed
- Zero new edge functions, zero new DB tables, zero new RPCs — all data from existing infrastructure

### [yono] Modal Rearchitecture: Batch-First, Scale-to-Zero
- **Created** `yono/modal_batch.py` — batch processing plane with Modal cron (*/15), CPU-only ONNX, direct Supabase writes, .map() burst workers, $0 idle
- **Created** `yono/modal_api.py` — API plane replacing yono-serve, min_containers=0, max_containers=4, scaledown_window=120s
- **Stopped** `yono-serve` Modal app (was leaking $33+/day with always-on containers)
- **Stopped** `yono-training-pipeline` Modal app (temporarily, to free billing headroom)
- **Unscheduled** pg_cron job 249 (yono-keepalive, every 5min) and 409 (yono-batch-process, every 5min)
- **Deleted** 3 edge functions from Supabase: `yono-keepalive`, `yono-batch-process`, `yono-vision-worker`
- **BLOCKED**: Modal deploy fails — billing cycle spend limit reached. Need to raise limit in Modal dashboard.
- Net: -3 edge functions, -2 cron jobs, -1 Modal app. +2 Modal apps pending deploy.

### [yono] Autonomous Daily Training Pipeline
- DB: `yono_model_registry` + `yono_training_metrics` tables created
- `modal_train.py`: saves metadata.json (run_id, best_val_acc, num_classes, total_samples, epochs, completed_at)
- `modal_serve.py`: added POST `/reload` endpoint for hot-swap ONNX models without redeploy
- `modal_continuous.py`: full rewrite (336→650 lines) — daily 2am UTC cron with 6 phases:
  - Phase 1 CHECK: query Supabase for new data, 5K threshold (was 10K weekly)
  - Phase 2 TRAIN: blocking .call() to train_make_classifier (15 epochs, was 30 fire-and-forget)
  - Phase 3 EVALUATE: fixed 500-image eval set, export candidate ONNX, compare vs production
  - Phase 4 PROMOTE/REJECT: copy ONNX to production, archive .prev, call /reload
  - Phase 5 HEALTH CHECK: 10 test images to /classify, verify confidence + latency
  - Phase 6 SELF-DEBUG: OOM→retry half batch, 3 consecutive failures→pause pipeline
- Manual actions: daily, evaluate, promote, rollback, health-check, build-eval-set, history, status, unpause
- `yono-keepalive`: surfaces training_pipeline status (ok/PAUSED) from yono_training_metrics

## 2026-03-12

### [vehicle-profile] Break the Loop — Typed Data Contract & Context

6-phase plan to stop recurring profile bugs (688 prompts for "profile looks wrong", 355 for "images not showing"). All phases complete.

**Phase 0 — Delete dead code:** Removed `vehicle-profile/VehicleProfile.tsx` (2,024-line dead copy) + `vehicle-profile-redesign.css` (2,971 lines, 1,341 `!important`). -4,997 lines.

**Phase 1 — Type contract:** Rewrote `types.ts` — removed `[key: string]: any` escape hatch from Vehicle interface. 190+ explicitly typed fields matching DB schema. Added `ImageRecord`, `TimelineEvent`, `VehicleComment`, `VehicleValuation`, `ExternalListing`, `ProfileStats`, `VehicleProfileData` interfaces. +589/-64 lines.

**Phase 2 — VehicleProfileContext:** Created context + provider + `useVehicleProfile()` hook. Centralizes data fetching, auth, permissions, realtime subscriptions, event listeners. Replaces 36 useState + 26-prop drilling pattern. 380 lines.

**Phase 3 — Image resolution:** Created `resolveVehicleImages.ts` — single deterministic DB query replacing 582-line `loadVehicleImages.ts` with 5 competing paths. 70 lines.

**Phase 4 — CSS audit:** Phase 0 deletion was the real win. Remaining 90 `!important` in `vehicle-profile.css` are legitimate Tailwind overrides. No changes needed.

**Phase 5 — Remove `window.__vehicleProfileRpcData`:** Removed all 9 references across 7 files. Each consumer now uses direct DB queries. -108 lines.

**Phase 6 — Quick wins:** Search RPCs already exist (7 functions). YONO unpause deferred (user decision, 33.5M images).

**Commits:** `8aef60b79`, `e28590b20`, `2d0410194`, `547d1f830`, `ffcff8f3c`, `7de0123e7`

## 2026-03-10

### [map] Event-Centric Map Rebuild — NukeMap

**DB:** Populated `vehicle_location_observations` with 265,517 coordinate observations from vehicle_images (6K GPS sightings) + vehicles table (62K high-conf, 16K low-conf, 183K null-conf listings). Added bbox/time/confidence indexes + RLS (public read ≥0.50, service_role full).

**Edge function:** Rewrote `map-vehicles` to query VLO instead of vehicles table. New params: `min_confidence`, `time_start`, `time_end`, `event_type`. Added `mode=histogram` endpoint returning monthly event counts for timeline. Server-side clustering via JOIN to vehicles for make/year/price filters.

**Frontend:** Deleted 2,700-line monolith (UnifiedMap.tsx + mapUtils.ts + old useMapLayers.ts + 824KB us-zips.json). Built modular 2,176-line replacement:
- `NukeMap.tsx` (208 lines) — DeckGL + MapLibre root, sidebar slot
- `hooks/useMapData.ts` — viewport-driven server fetch (debounced 300ms)
- `hooks/useMapTimeline.ts` — server histogram + temporal filtering
- `hooks/useMapLayers.ts` (56 lines vs 721) — builds layers from server data
- `hooks/useMapSidebar.ts` — stack-based push/pop navigation
- `layers/` — eventPointLayer, clusterLayer, businessLayer, heatmapLayer
- `controls/` — MapTimeline, MapLayerPanel, MapSearchBar
- `panels/EventPinDetail.tsx` — event type badge, confidence tier, vehicle link
- `types.ts`, `constants.ts`, `mapService.ts` — shared types + API calls

**Key changes:**
- No more `geo()` fake geocoding — no coordinate = no pin
- Server-driven data — no client-side 195K vehicle array
- Timeline operates on `observed_at` not `created_at`
- Confidence tiers: VERIFIED (≥0.85), CITY (0.70-0.84), APPROX (0.50-0.69)
- Default filter: ≥0.70 (~103K pins), toggle for "Show approximate" (≥0.50, ~265K)
- ZCTA boundary file uploaded to Supabase Storage `map-data` bucket (public)

### [widgets] Inference Popup Layer — All 3 Widgets
- Shared popup infrastructure in NukeWidgetBase (showPopup, dismissPopup, PopupRow type)
- nuke-vehicle: 44 clickable data points (specs, valuation, signal weights, condition, build record, mods, provenance, community, comps)
- nuke-valuation: 8+ clickable points (value breakdown, heat, deal, confidence, comps)
- nuke-vision: All cells clickable (identification, value, condition, zone, alternates, comps)
- Every popup shows computed inference from available data (percentiles, premiums, ROI, trends, rarity)

### [orchestrator] 22-Agent Deep Execution Sprint
- 12 research + 10 execution agents, 19 reports in `.claude/reports/`
- 505,442 duplicates marked, 13,068 impossible states fixed, YONO cron enabled, 3 BJ crons killed
- yono-batch-process 4 bugs fixed, archiveFetch storage fallback added
- All frontend ingestion wired through `ingest`. NotificationCenter icons. Image mismatch filtering.
- 3,264 identity claim stats populated ($555M GMV). SDK v2.0.0 + MCP v0.3.0 ready (blocked on npm login)
- 14 MCP registries prepped, 1 submitted, 2 PR branches ready. K10 demo: $175K, score 92, showcase.

### [search] Search Pagination — Users Can Now See All Results
- **Root cause**: Search pipeline had hard caps at every layer (limit 100, no offset, no pagination). "jimmy" showed ~94 of 410 matches. "Mustang" showed ~95 of 31,392.
- **Backend**: Added `offset` param to `universal-search` edge function. Page 1 uses RPC for ranking; page 2+ uses ILIKE with `.range()`. Added `count_vehicles_search` RPC (parallel, 5s timeout). Response includes `meta: { total_count, offset, limit, has_more }`.
- **Frontend**: `SearchMeta` interface, `onSearchMeta` callback, `handleLoadMore` with dedup/append, "Load More" button + "X of Y" count display.
- **Fix**: Dropped duplicate `search_vehicles_fts` function signature causing PGRST ambiguity failures.
- **Verified**: jimmy → 410 total, mustang → 31,392 total, pagination returns distinct pages.

### [infra] Database Storage Emergency — 171 GB → 78 GB
- Dropped 39 duplicate/unused indexes on vehicle_images and vehicles (~12 GB)
- VACUUM FULL on cron.job_run_details (1.2 GB → 8 MB), added daily cleanup cron
- Deleted 250K failed snapshots (zero content)
- Dropped ~463 empty tables
- Migrated 336K listing_page_snapshots HTML to Supabase Storage bucket `listing-snapshots`
  - Storage path: `{platform}/{YYYY}/{MM}/{DD}/{id}.html`
  - Updated `archiveFetch.ts` to read transparently from Storage when html column is NULL
  - Script: `scripts/migrate-snapshots.mjs` (parallel workers, FOR UPDATE SKIP LOCKED)
  - Edge function: `migrate-snapshots-to-storage` with RPC bypass for PostgREST
  - Created RPC functions: get_snapshots_to_migrate, mark_snapshot_migrated, count_snapshots_remaining
  - Created partial index: idx_lps_needs_migration
- VACUUM FULL listing_page_snapshots: 79 GB → 339 MB
- Total: 93 GB reclaimed, 0 data lost

### [data] Post-Purge Cleanup & Data Quality
- **Repo hygiene**: Removed 80+ junk files from git tracking (YC drafts, .ralph/, agent notes, one-shot fix scripts). Updated .gitignore. Already pushed to GitHub.
- **Make normalization**: Collapsed 12,093 distinct makes → single canonical spelling per make. Zero variant groups remaining. Handled acronyms (BMW/GMC/AMC/MG/MINI/TVR), hyphenated (Mercedes-Benz, Rolls-Royce), special casing (McLaren, DeLorean, DeSoto).
- **Quality score recalibration**: Updated `compute_vehicle_quality_score()` to use `primary_image_url` (not `listing_url` proxy). Re-scored 552K vehicles. New distribution: avg 75.1, median 60 (previously inflated ~90+ for all).
- **Model normalization**: Collapsed 12,362 variant groups to zero. Used `normalize_models_batch()` (SECURITY DEFINER, triggers bypassed) with temp index on `LOWER(model)`. Key insight: partial index requires explicit `model IS NOT NULL AND model <> ''` in queries for planner to use it. Temp index and function cleaned up after completion.

## 2026-03-09

### [images] Image Integrity Audit & Fix — 5 Problems Resolved
- **FB CDN Rescue**: Created `scripts/rescue-fb-cdn-images.mjs` — rescued 615 expiring FB CDN primary images to Supabase storage, nulled 1,481 already-expired URLs. Zero FB CDN URLs remain in `primary_image_url`.
- **FB Scraper Hardened**: `fb-marketplace-local-scraper.mjs` no longer falls back to CDN URLs on download failure (skips insertion). `import-fb-marketplace` edge function also downloads to storage before inserting.
- **Placeholder iPhoto Cleanup**: Deleted 8,199 `placeholder.nuke.app` records from `vehicle_images`. Hardened `--map-only` mode to write local JSON (`data/iphoto-mappings/{vehicleId}.json`) instead of DB placeholders.
- **Cross-Link Dedup**: Deleted 165 duplicate BaT `vehicle_events` (same URL linked to 2 vehicles). Added frontend cross-link guards in `loadVehicleImages.ts`.
- **Image Count Backfill**: Enhanced `scripts/backfill-image-counts.mjs` with `--fix-all` mode that syncs ALL active vehicles, not just `image_count=0`.
- **Broken Triggers Dropped**: Removed `trigger_check_vehicle_images_on_image_delete/insert` + 4 functions referencing missing `standing_orders` table.
- **Frontend Fix**: Fixed `loadVehicleData.ts` fallback query — was referencing `source_platform` (should be `platform_source`) and `exterior_color` (doesn't exist), causing "Vehicle Not Found" when RPC timed out.
- **Deep Junk Audit**: Deleted 63K+ junk `vehicle_images`: `yolo_scan` 17,472 file://, `facebook_marketplace` 31,986 expired CDN, `photos_library` 8,764 file://, `owner_import` 4,400 placehold.co, `video_scan` 203 file://, `dealer_scrape` 298 social share links. Nulled ~260 garbage `primary_image_url` (FB tracking pixels, literal "jpg", file://).

### [yono] Condition Spectrometer — ALL PHASES COMPLETE (1-5)
- **Phase 1A**: Applied migration creating 5 tables: `condition_taxonomy`, `condition_aliases`, `image_condition_observations`, `vehicle_condition_scores`, `condition_distributions` — all with RLS, indexes, proper constraints
- **Phase 1B**: Seeded 47 condition descriptors across 5 domains (exterior 25, interior 6, mechanical 6, structural 5, provenance 5) + 15 legacy aliases mapping existing damage_flags/modification_flags
- **Phase 2A**: Fixed `build_ymm_knowledge.py` v2 — filters seller comments (`is_seller=false`), coalesces model variants (Camaro Z28+SS+Convertible → base Camaro), removed regex mod extraction (60-70% false positive), added lifecycle + condition distributions from vision data
- **Phase 2B**: Rebuilt 485 v2 profiles (coalesced), deleted 166 superseded v1 profiles. 29 v1-only profiles remain for Y/M/M combos not covered by v2 rebuild
- **Phase 3A-4A**: Built `yono/condition_spectrometer.py` — 5W context function (free metadata before vision), observation writer bridge (YONO v1 output → taxonomy-mapped observations), 0-100 condition score aggregator (5-domain rubric), distribution computer with rarity signals
- **Phase 3C**: Contextual pass — loads Y/M/M knowledge profile, generates rarity signals (lifecycle frequency vs Y/M/M norm), unexpected condition flags, coverage gap analysis
- **Phase 3D**: Sequence pass — zone imbalance detection, multi-angle damage confirmation, sequence pattern analysis (systematic_walkthrough/semi_organized/random_shots), coverage completeness
- **Phase 4B-4C**: Batch scoring (`score-all` CLI), distribution recomputation, rarity = 1 - CDF(score, ymm_distribution)
- **Phase 5**: Taxonomy growth pipeline (`grow` CLI) — discovers unmapped flags, auto-creates taxonomy nodes + aliases with versioning. First run: 30 new descriptors (69 total, up from 47 initial seed). Covers damage types (hail, flood, fire, frame), interior conditions (headliner, carpet, dash), and mechanical mods (turbo, headers, disc brakes, etc.)
- **Full pipeline CLI**: `pipeline --vehicle-id UUID` runs all 5 steps: bridge → contextual → sequence → score → distribute. Tested on 1974 Blazer: 104 observations bridged, 4 sequence signals, 35/100 "project" tier
- **Server endpoints**: 7 condition endpoints total — `/condition/context`, `/condition/bridge`, `/condition/score`, `/condition/contextual`, `/condition/sequence`, `/condition/pipeline`, `/condition/distribute`
- **Auto-observation wiring**: `/analyze` endpoint auto-writes observations when `image_id` + `vehicle_id` provided
- Tested end-to-end: bridge 26 images → 26 observations for a vehicle → 35/100 "project" score with lifecycle="ghost". Second vehicle: 63.5/100 "driver" tier, lifecycle="weathered"
- Variant coalescing verified: 1969 Camaro now 1,899 vehicles (was split across 5 profiles), 1957 Thunderbird 1,260 (was 2)

### [triage] Phase 4: Dead Vehicle Deletion + Empty Table Cleanup + Snapshot Retention
- Deleted 561,758 dead vehicles (8K deleted + 48K merged + 505K duplicate) with full cascade cleanup
- Vehicles table: 1,291,950 → 730,192 (43% reduction)
- Pre-deleted ~2M child rows for performance (vehicle_images 648K, vehicle_status_metadata 501K, vehicle_price_history 389K, duplicate_detection_jobs 436K)
- Dropped 75+ FK constraints (NO ACTION + SET NULL + circular) blocking deletion
- Disabled/re-enabled 32 triggers on vehicles during bulk delete
- VACUUM ANALYZE completed on all affected tables (vehicles, vehicle_images, vehicle_price_history, vehicle_status_metadata, duplicate_detection_jobs, ai_scan_sessions, bat_extraction_queue, timeline_events)
- Dropped 41 empty tables (22 safe orphans + 19 dangerous FK parents after dropping 24 FK constraints)
- Tables: 555 → 514, zero empty tables remaining
- Deleting 283K duplicate listing_page_snapshots (keeping newest per URL) — ~36 GB recovery expected
- PostgREST schema reloaded after all DDL

### [triage] Phase 5: Edge Function Consolidation (297 → 228 deployed)
- Deleted 69 edge functions from Supabase (remote) + local codebase
- **Tier 1 (deleted features, 12):** api-v1-exchange, investor-portal-stats, send-shipping-notification, 5x vault-*, paper-trade-autopilot, backtest-hammer-simulator, place-market-order, update-exchange-prices
- **Tier 2 (deprecated, 4):** bat-simple-extract, smart-extraction-router, extract-using-catalog, extract-collecting-cars
- **Tier 3 (zero-caller dead functions, 53):** admin-pulse, agent-monitor, health, vision-analyze-image, 5x ds-*, telegram-*, instagram-*, fb-marketplace-bot/sweep, backfill-bonhams/cb/primary-images/vehicle-counts, analyze-auction-comments/market-signals/vehicle-description, auction-intelligence, data-quality-monitor/workforce, deal-brief/wire-automation, decompose-deal-jacket, search (replaced by universal-search), +20 more one-off/abandoned functions
- Unscheduled 2 cron jobs referencing deleted functions (hammer-daily-health-check, collecting-cars-detail-backfill)
- Protected 117 zero-caller functions that are called indirectly (API endpoints, webhooks, core extractors, YONO, infrastructure)
- Local dirs: 443 → 387
- Remaining 228 deployed functions to be further consolidated to ~50 in Phase C (future work)

### [yono] Contextual Intelligence Pipeline — Phase 1-4 Infrastructure
- Created `ymm_knowledge` DB table for pre-computed Y/M/M knowledge profiles
- Built `yono/contextual_training/build_ymm_knowledge.py` — aggregates raw auction_comments (11.6M rows), vehicle specs, and vision labels into structured Y/M/M profiles. Pure SQL + deterministic regex, no AI synthesis.
- Built `yono/contextual_training/featurizers.py` — converts profiles to 133D float vectors (103D YMM + 20D vehicle + 10D timeline)
- Extended `modal_contextual_train.py` with ContextualModelV3 — EfficientNet-B0 + 133D context → 5 multi-task heads (zone/condition/damage/mods/price), context dropout 20%, class-rebalanced BCEWithLogitsLoss with pos_weight
- Updated `export_contextual_data.py` v2 — joins with ymm_knowledge feature vectors for training data
- Added `ContextualYONOClassifier` to `yono/yono.py` — local ONNX inference, Y/M/M context from Parquet, zero API calls
- Added `/analyze/contextual` endpoint to `yono/server.py`
- Built 100+ Y/M/M profiles (500 batch in progress): 1969 Camaro (997 vehicles, engine swaps, axle ratios, wheel types), 1965 Mustang, 1967 Corvette, etc.
- Data quality stance: ONLY raw auction_comments + vehicle specs. comment_discoveries excluded (57.6% hollow, 98% programmatic-v1)

## 2026-03-08

### [data-quality] Canonical Makes Deduplication
- Merged 14 duplicate canonical_makes entries (UPPERCASE + Title Case variants) to UPPERCASE only
- Re-pointed 50,636 vehicles from Title Case → UPPERCASE canonical_make_id
- Deleted 14 orphaned Title Case entries — zero duplicates remaining (152 canonical_makes total)
- Used batched UPDATEs (500 rows/batch, pg_sleep(0.2)) to avoid lock contention
- Rejected 500 garbage-make active vehicles (makes starting with non-letter, single char, or all-numeric)
- Feed make filter now works correctly with single canonical form

### [data-quality] Vehicle Make Casing Normalization
- Normalized ALL make casing variants in vehicles table — 0 variant groups remain (was ~900+)
- ~898 distinct makes normalized, ~12,600+ total rows updated across all vehicle statuses
- Uppercase acronyms preserved: AC, MGB, MGA, TVR, NSU, DKW, BSA, ISO, ASA, HRG, AMG, BMC, DMC, BRM, AJS, GM, VW, FN, MV, BAC, AAR, GAZ, DAF, UAZ, LTI, CMC, CAV, GPK, NASCAR, SCCA, REO, OSCA, ERA, etc.
- Mixed-case preserved: DeSoto, LaSalle, De Tomaso, Hispano-Suiza, AutoKraft, McCulloch, McCormick, EZ-GO, Vincent-HRD, AM General
- Hyphenated properly capitalized: Pierce-Arrow, Talbot-Lago, Dual-Ghia, Nash-Healey, Coca-Cola, etc.
- All remaining makes normalized to Title Case via INITCAP
- Used batched UPDATEs (500 rows/batch, pg_sleep) to avoid lock contention

### [platform] Vercel Build Fix
- Fixed `.vercelignore` stripping `package-lock.json` (caused inconsistent builds)
- Deleted dead `useBettingWallet.ts` hook (zero importers)
- All Vercel deployments now green

### [data-quality] The Great Vehicle Classification — Phase 2 (continued)
- Rejected 484 remaining non-auto vehicles (MOTORCYCLE, BOAT, TRAILER, etc.) still marked active
- Launched 3 parallel sub-agents for: BMW/Honda/Triumph model-based classification, garbage make cleanup, primary_image_url backfill
- BMW/Honda/Triumph agent classifying 11.7K mixed-make vehicles by model name (R-series → MOTORCYCLE, 3 Series → CAR, X5 → SUV, etc.)
- Garbage makes agent cleaning "The" (266), "Broad" (198), "Automobiles" (172), "Factory" (149), and other parsing errors
- Image backfill agent filling primary_image_url from vehicle_images table (41% → target 60%+)
- Progress so far: NULL canonical_vehicle_type dropped from 340K → 13,752 (96% classified)
- Final active distribution: CAR 529,480 | TRUCK 49,891 | SUV 33,172 | VAN 2,368 | BUS 653 | MINIVAN 315 | NULL 13,752
- Total active vehicles: 629,631
- Classified by make: Ford, Mercedes-Benz, Chevrolet, Porsche, VW, GMC, Alfa Romeo, Aston Martin, etc.
- Rejected non-auto: Boston Whaler, Grady-White, Carver, Malibu (boats), Douglas, Zundapp, Harley-Davidson (motorcycles), Clark, Massey-Ferguson (equipment), memorabilia brands (Coca-Cola, Pepsi, Breitling, etc.)
- Rejected garbage: emojis, numbers, punctuation, single-char makes, null-make/null-title/null-year junk (~16K)
- Remaining 13.7K NULL: ~7,000 fragmented makes (avg 2 records) + mixed kit/custom (ASVE, SPCN) — needs NLP/title parsing
- YONO sidecar confirmed healthy: all models loaded (tier1, 7 tier2 families, flat, vision, zone classifier)
- YONO batch pipeline E2E tested: 108 images classified, 30% high confidence, 1.7 img/s throughput
- 34.2M images pending — need 50+ parallel Modal workers for reasonable timeline (~5 days)

### [yono] Nuke Agent LLM Training Data
- Created training data file: `yono/training_data/train.jsonl`
- 187 total examples covering: platform ops, vehicle domain, data quality, extraction, valuation, YONO, SDK, market intel, troubleshooting
- Combined with 2,049 existing examples on Modal volume = 2,236 total training examples
- Training infrastructure ready: `yono/modal_nuke_agent_train.py` (Qwen2.5-7B QLoRA on A100)
- Contextual training data export script ready: `yono/contextual_training/export_contextual_data.py`

### [infra] Vercel Build Fix
- Root cause: `.vercelignore` had `*.lock` which stripped `package-lock.json` from git-triggered builds
- Without lockfile, `npm install` resolved different Rollup versions that treated missing dynamic imports as fatal
- The missing imports were `TradePanel` and `OrganizationInvestmentCard` (dead feature stubs not committed)
- Stubs were already added in `b4fa118ab` but the `*.lock` exclusion remained a risk
- Fix: Removed `*.lock` from `.vercelignore`, deleted dead `useBettingWallet.ts` hook (zero importers)
- Verified: deployment `eac3187e` built successfully on Vercel

### [yono] Image Pipeline Unstick + YONO Processing
- Released 28,149 stuck image processing locks (orphaned since Feb 15-18)
- Fixed 4 bugs in yono-batch-process edge function:
  - Invalid PostgREST `.is("image_url", "not.null")` filter (function was completely broken)
  - Missing MODAL_SIDECAR_TOKEN auth header (all classify calls returned Unauthorized)
  - Invalid `yono_complete` status value (violates CHECK constraint, changed to `completed`)
  - Query timeout on 34M rows (changed IN filter to EQ for partial index, removed count query)
- Updated stale MODAL_SIDECAR_TOKEN in Supabase secrets
- Processed 1,624 images through YONO classification
- Three high-value Ferraris processed: 250 GTO ($38.5M, 77%), 250 GT SWB California Spider ($25.3M, 99%), 250 GT ($17.9M, 100%)
- Pipeline throughput: 25 img/s via edge function, 2.5 img/s via daily_progress.mjs
- NUKE_ANALYSIS_PAUSED confirmed UNSET (not blocking)
- Modal sidecar confirmed healthy (classify + vision, tier-1 + 7 tier-2 families)
- Report: .claude/reports/image-pipeline-unstick.md

### [data-purge] Great Data Purge Audit — READ-ONLY (Prompt 4)
- Full audit of 1,291,572 vehicles table for bloat classification
- Found 502,587 duplicates (496K purgeable with zero relations, ZERO have merged_into_vehicle_id)
- Found 35,640 ConceptCarz empty shells (no VIN, no images, no events)
- Found 13,068 impossible states (active + ended auction + sale_price)
- Found 502,346 excess listing_url duplicates across 53,150 unique URLs
- Found 10,151 true orphans (no URL, no VIN, no images, no events)
- Found 54,318 purgeable rejected and 8,327 purgeable deleted records
- Estimated 43.3% row reduction (1.29M -> 733K), 3.7 GB savings
- 198 FK references from 176 dependent tables documented
- Full migration plan with batched SQL templates (not executed)
- Report: `.claude/reports/data-purge-audit.md`

### Ghost Cron Cleanup — Stop Burning Compute on Nothing
- [crons] Killed 16 ghost cron jobs: 3 financial ghosts (update-exchange-prices, refresh_investor_portal_stats, paper-trade-autopilot), 6 retired CQP crons (390-395), 1 anon-key security issue (enrich-bulk #157), 3 calling non-existent edge functions (process-catalog-queue, service-orchestrator, auction-scheduler), 8 already-disabled entries cleaned from table
- [crons] Fixed 4 Hard Rule #3 violations: parse_bat_snapshots_bulk x2, document_ocr_queue lock release, batch-extract-snapshots — all moved from 3min to 5min intervals
- [data] Released 28,149 stuck vehicle_images processing locks (oldest from Feb 15, 20+ days old) via batched UPDATE with FOR UPDATE SKIP LOCKED
- [crons] Zero Hard Rule #3 violations remain. Active crons: 100 (down from 110+). Sub-5-min crons: 0 (down from 10)
- [crons] Estimated savings: ~112,320 edge function invocations/month (~$1,100-2,200/month)
- [report] Full cleanup documented at .claude/reports/ghost-cron-cleanup.md

### Patient Zero K10 Fix — Make It Perfect
- [k10] OWNER LINKED: Set owner_id, uploaded_by, created_by_user_id to Skylar's auth user (13450c45). ownership_verified=true, verification_status=title_verified, confidence_score=100
- [k10] DESCRIPTION WRITTEN: 643-char owner description covering the full restomod build — frame-off, $124K, 6,580 labor minutes, 17-month build
- [k10] HIGHLIGHTS/MODS/EQUIPMENT: 8 highlights, 10 modifications, 8 equipment items populated
- [k10] VALUATION CONTEXT: purchase_price=$124K, asking_price=$175K, condition_rating=9/10, is_modified=true
- [k10] DISPLAY TIER: Upgraded from "browse" to "showcase"
- [k10] 5 OBSERVATIONS CREATED: specification (restomod build), work_record (6,580 min, 10 phases), condition (9/10 excellent), valuation ($150-250K range), provenance (founder's vehicle)
- [k10] VALUATION RECORD: $175K estimate with 6 comparable sales ($80K-$228K range) inserted into vehicle_valuations
- [k10] DATA QUALITY SCORE: 70 -> 85 via recalculate_quality_score()
- [k10] YONO PROCESSING STARTED: 8 images classified via yono-classify (all identified as American vehicles), 1 analyzed via yono-analyze (zone: detail_badge)
- [k10] VALUATION RECOMPUTE: compute-vehicle-valuation triggered (automated comp-based estimate: $25K — still blind to restomods)
- [k10] iPHOTO INTAKE: Re-triggered with --force flag for missing 302 photos (running in background)
- [k10] REMAINING: nuke_estimate still pipeline-computed at $25K (needs restomod-aware valuation logic), 117 images still ai_processing_status=pending (global NUKE_ANALYSIS_PAUSED blocks batch processing)

### Engagement Infrastructure Activation
- [engagement] Verified engagement tables: user_subscriptions (0->10 rows), user_notifications (18->21), email_digest_queue (0), follow_roi_tracking (0)
- [engagement] CRITICAL FIX: user_subscriptions had RLS DISABLED — enabled RLS + created 5 policies (SELECT/INSERT/UPDATE/DELETE for own rows + service_role ALL)
- [engagement] Added unique constraint (user_id, target_id, subscription_type) to prevent duplicate follows
- [engagement] Created 10 vehicle subscriptions for Skylar across both accounts (K10, K5 Blazer, C-10, Mustang, Jimmy, LX450, K2500, Roadster, 2x Bronco)
- [engagement] Created 3 test vehicle_update notifications (K10 YONO analysis, K5 Blazer comp found, C-10 price estimate)
- [engagement] Deployed `notify_subscribers_on_observation()` trigger on vehicle_observations — automatically notifies subscribers when new observations land
- [engagement] 1-hour throttle prevents notification spam per user per vehicle
- [engagement] Report: .claude/reports/engagement-activation.md

### Wire Ingest Function to Frontend
- [frontend] Wired `AIDataIngestionSearch.tsx` URL paste/enter flow through the `ingest` edge function
  - Previously: URL -> `extract-vehicle-data-ai` -> preview -> manual confirm -> `dataRouter`
  - Now: URL -> `ingest` (handles source detection, dedup, enrichment, vehicle creation, user linking)
  - Falls back to legacy flow if ingest fails
- [frontend] Added VIN fast-path: 17-char VIN entry -> `ingest({ vin })` -> vehicle created/matched
  - Previously: VIN -> NHTSA decode -> preview only (no creation)
  - Now: VIN -> `ingest` -> vehicle created or matched, navigate to profile
- [frontend] Added `ingestVehicle()` function in `aiDataIngestion.ts` — typed wrapper for `ingest` edge function
- [frontend] Auto-ingest on URL paste: pasting a URL triggers immediate ingestion without extra Enter press
- All 12 source platforms now get dedup + user discovery linking on every URL submission

### The Great Vehicle Classification — 340K Records Cleaned
- [data] Step 1: Classified ~68K records by body_style (Convertible→CAR, Coupe→CAR, Truck→TRUCK, SUV→SUV, etc.)
- [data] Step 2: Classified ~225K records by make (Ford, Chevrolet, Ferrari, Mercedes-Benz, Porsche + 100s of smaller makes → CAR/TRUCK/SUV)
- [data] Step 2: Classified motorcycle makes (Harley-Davidson, Yamaha, Ducati, Indian, etc. → MOTORCYCLE)
- [data] Step 2: Classified boats (Chris-Craft, Riva, Donzi, etc. → BOAT), trailers, RVs, heavy equipment
- [data] Step 2: Classified memorabilia/junk (Rolex, Fender, Coca Cola, etc. → OTHER)
- [data] Step 2: Left mixed makes NULL per plan (BMW 7K, Honda 3.2K, Triumph 1.5K — need model-level classification)
- [data] Step 3: Rejected ~36K non-auto vehicles (MOTORCYCLE, BOAT, HEAVY_EQUIPMENT, TRAILER, ATV, UTV, SNOWMOBILE, RV, OTHER, non_vehicle → status='rejected')
- [data] Step 3: Rejected by source_listing_category (Motorcycles, Boats, RVs, Go-Karts, Tractors, Parts)
- [data] Result: 653,894 active vehicles — 520K CAR, 50K TRUCK, 33K SUV, 47K still NULL (mixed/junk makes), 2.4K VAN, 665 BUS, 315 MINIVAN
- [data] Before: 340K NULL canonical_vehicle_type, non-auto junk in feeds. After: 47K NULL (intentionally ambiguous), all non-auto rejected

### YONO Daily Progress Machine
- [yono] Created `yono/daily_progress.mjs` — local batch classifier for 34M pending images
  - Fetches pending images from vehicle_images, sends to YONO sidecar (Modal), writes results back
  - Idempotent row-level locking, resumable, batched writes (respects BATCHED MIGRATION PRINCIPLE)
  - Modes: --report-only, --dry-run, --unstick, --vehicle-id, --limit
  - Logs metrics to logs/yono-daily-YYYY-MM-DD.json (confidence distribution, throughput, top makes)
- [yono] Added 4 npm scripts: yono:daily, yono:daily:dry, yono:daily:report, yono:daily:unstick
- [yono] Verified end-to-end: 10 images classified via Modal sidecar, 4 high-conf marked completed, 0 errors
- [yono] Full audit report at .claude/reports/yono-daily-progress-audit.md:
  - 34.2M pending, 887K completed, 28K stuck in 'processing'
  - 875K labeled training records, 1,634 makes (545 with <10 examples — needs cleanup)
  - Modal sidecar ONLINE (classify + vision), 7 tier-2 family models
  - COLMAP installed and ready (v3.13.0), bat_reconstruct.py complete, 1 test reconstruction done
  - Image cache empty (91K cached images previously purged)

### Surface the Damn Data — Backend→UI Data Gap Fix
- [search] Denormalized `image_count` and `observation_count` as columns on `vehicles` table
- [search] Added triggers (`trg_vehicle_images_count`, `trg_vehicle_observations_count`) to keep counts in sync
- [search] Backfilled 265K vehicles with real image counts, 39K with observation counts (100% complete)
- [search] Built `scripts/backfill-image-counts.mjs` — cursor-paginated, lock-aware, resumable
- [search] Updated `universal-search` edge function to read counts from `vehicles` table directly (no runtime enrichment)
- [search] Removed unreliable `enrichWithCounts` function (30 parallel HEAD queries silently failing)
- [search] VIN search now case-insensitive via `ilike` + partial match fallback
- [db] Created migration `20260308030000_denormalize_vehicle_counts.sql`
- [db] Created `backfill-vehicle-counts` edge function for ongoing backfill
- [db] Backfilled 1,355 vehicles with `primary_image_url` via `backfill_primary_image_url` RPC
- [db] Recalculated quality scores for 2,050 vehicles with new formula (includes image/observation counts)
- [frontend] Updated `VehicleCardDense` tier calculation to use `observation_count` and `image_count`
- [frontend] Restored `QuickStatsBar` in vehicle profile with observation count
- [frontend] Updated `SearchResults.tsx` to pass `observation_count` to cards

## 2026-03-07

### The Great Data Purge — Data Quality Emergency Fix

**Phase 1: Audit** (read-only)
- [data] Full audit: 1,291,547 vehicles → 743,079 distinct URLs (42% bloat)
- [data] BaT: 620K rows, 160K distinct URLs (3.9x bloat), top listing had 374 copies
- [data] Cars & Bids: 41K rows, 1,085 distinct URLs (38x bloat)
- [data] Collecting Cars: 9.5x bloat, ConceptCarz: 35K shells (97.5% empty)
- [data] 358,650 impossible states (duplicate + active auction_status)
- [data] 467K empty shells identified (no desc, no image, no price, no VIN, no mileage)

**Phase 2: Normalize Source Names**
- [data] Fixed `bonhams_JUNK_DELETE_ME` → `bonhams` (200 rows)
- [data] Fixed `Craigslist` → `craigslist`, `BaT` → `bat` case splits

**Phase 3: Collapse BaT Active Duplicates**
- [data] 2,655 BaT active duplicate rows merged (kept best row per URL)
- [data] Fixed trailing-slash URL variants (33 slash pairs merged)

**Phase 4: Purge Empty Shells**
- [data] 33,204 ConceptCarz empty shells → status='rejected' (97.5% had zero useful data)
- [data] 5,382 cross-source empty shells rejected (no YMM, no desc, no image, no price)

**Phase 5: Fix Impossible States** — COMPLETE
- [data] 655,517 duplicate rows: cleared auction_status (358,650 active + 296,867 ended) across 2 sessions
- [data] ~75,000 duplicate rows: cleared reserve_status
- [data] Fixed sold+reserve_not_met → reserve_met (8 rows)
- [data] Fixed merged+active_auction (243), rejected+active_auction (376)
- [data] Final verification: ALL impossible states at ZERO
- Scripts: `scripts/fix-dup-auction-robust.sh` (final working version), `scripts/merge-bat-dupes-v2.sql`

### Image-Vehicle Match Integrity Pipeline
- [db] Added `image_vehicle_match_status` column to `vehicle_images` (confirmed/mismatch/ambiguous/unrelated)
- [edge] Created `check-image-vehicle-match` — Claude Haiku vision validates images match assigned vehicle
- [edge] Wired async validation into `extract-jamesedition` and `extract-bat-core` extractors
- [cron] Job #385: runs every 5 min, processes 20 images/batch
- [script] `scripts/run-image-match.mjs` — batch worker for parallel processing
- [frontend] Added `.not('image_vehicle_match_status', 'in', '("mismatch","unrelated")')` filter to ALL 14 user-facing image query points:
  - loadVehicleImages, ImageGallery (4), useVehicleImages, VehicleImageGallery (2)
  - VehiclePortfolio (2), VehicleThumbnail, CursorHomepage, EnhancedDealerInventory (2)
  - SocialWorkspace, StorefrontVehicleDetail, VehicleProfile (2)
- [edge] Wired async validation into `extract-cars-and-bids-core` extractor (deployed)
- [data] JamesEdition: 595 images validated, 11.3% mismatch rate
- [data] Processing 694K dealer images across mecum/gooding/broad_arrow/pcarmarket/fb_marketplace
- [data] ~43K images processed, 2,268 mismatches caught. Mismatch rates: PCarMarket 44%, JamesEdition 17-20%, Mecum 7-9%, Gooding 6%, Broad Arrow 5%
- [data] 29.5K FB Marketplace images marked ambiguous (expired CDN URLs, need base64 approach)
- [fix] Fixed false-orphan bug: edge function now fails loudly when vehicle lookup returns 0 results instead of marking valid images as unrelated. Reversed 350 false orphans.
- [fix] Fixed infinite retry loop: images that fail vision API now marked as "ambiguous" instead of being reprocessed forever
- [fix] Fixed FB CDN detection: fbcdn.net URLs detected early and marked ambiguous without API call

### PLATFORM TRIAGE — Critical Infrastructure Cleanup

**Phase 0: Stop the Bleeding**
- [db] Killed 15 broken cron jobs: 2 bat-queue-worker 404s (2,880/day), 10 valuation shard timeouts (every 2 min), deadlocking quality-backfill-fast, micro-scrape-bandaid 404, refresh-vehicle-valuation-feed (deleted view)
- [security] Revoked anon access on `user_verification_status` view (was exposing emails/phones to unauthenticated users)
- [db] Released 28,149 stuck vehicle_images from "processing" → "pending"
- [db] Fixed "complete" vs "completed" status inconsistency (1,300 rows)

**Phase 1: Database Triage**
- [db] Dropped ~2.5 GB of unused indexes (17 non-constraint indexes with 0 scans across vehicle_images, bat_bids, scraping_health, auction_comments, field_extraction_log, observations, import_queue, etc.)
- [db] Database size: 171 GB → 156 GB (15 GB reclaimed from index drops)
- [db] Created missing composite index `idx_vehicles_valuation_candidates` (was causing all 10 valuation shards to timeout)
- [db] Re-enabled valuation as 1 consolidated cron every 15 min (was 10 shards every 2 min)
- [db] VACUUM ANALYZE on 6 never-vacuumed tables: auction_comments (1.5M dead tuples), bat_bids (714K), vehicle_observations, field_extraction_log, scraping_health, timeline_events

**Phase 2: Codebase Surgery**
- [cleanup] Deleted 18 dead-feature edge functions: betting (4), trading (7), vault (5), concierge (2)
- [cleanup] Deleted `_archived/` directory (259 archived edge functions, zero purpose)
- [cleanup] Deleted 9 deprecated duplicate extractors: bat-extract, bat-simple-extract, extract-collecting-cars-simple, extract-vehicle-data-ollama, extract-and-route-data, smart-extraction-router, extract-using-catalog, extract-with-proof-and-backfill, analyze-image
- [cleanup] Deleted deprecated shared modules: predictionEngine.ts, hybridFetcher.ts
- [cleanup] Deleted dead backends: nuke_api/ (164 MB Elixir), nuke_backend/
- [cleanup] Deleted 16 junk files from nuke_frontend/ root (fix-imports scripts, SQL files, test HTMLs)
- [cleanup] Deleted 20 dead frontend files: trading components, vault pages, investor pages/components
- [cleanup] Fixed broken imports in DomainRoutes.tsx, marketplace routes, Capsule.tsx, Portfolio.tsx, compliance/index.ts
- [cleanup] Edge function count: 464 → 440 (+ 259 archived deleted)

**Phase 3: Cost Optimization**
- [crons] Eliminated ALL every-1-minute crons (was 10 jobs, now 0)
- [crons] Eliminated ALL every-2-minute crons (was 15 jobs, now 0)
- [crons] check-image-vehicle-match: every 1 min → every 10 min (#1 AI cost at ~$2,100/mo)
- [crons] haiku-extraction-worker: every 2 min → every 5 min
- [crons] BAT extraction: 3 workers every 2 min → 1 worker every 10 min
- [crons] CQP workers: removed duplicates (cnb-2, mecum-2, mecum-live-2), remaining → every 5 min
- [crons] Enrichment crons: every 2 min → every 10 min
- [crons] VIN enrichment: every 3 min → every 15 min
- [crons] YONO vision workers: disabled (pipeline PAUSED)
- [crons] Fixed 4 crons using anon key instead of service role key
- [crons] Active crons: 131 → 112, every-minute invocations: 14,400/day → 0

**Phase 5: Governance**
- [docs] Added 10 HARD RULES to CLAUDE.md preventing future bloat
- [docs] Updated edge function count from "181" to "~440 (target: 50)"
- [docs] Logged all triage work to DONE.md

**Estimated impact:**
- Database: 171 GB → 156 GB (15 GB reclaimed, more from VACUUMs)
- Monthly burn: reduced by ~$1,500-3,000/mo (cron frequency + AI cost reduction)
- Cron invocations: ~41,000/day → ~15,000/day (63% reduction)
- Deadlocks: eliminated (quality-backfill-fast killed, valuation shards consolidated)
- Security: auth.users exposure to anon closed

[ops] CWTFO Dashboard (Admin Pulse) — single-page "Is Everything Working?" dashboard
  - Created `admin_pulse()` RPC — single query returns queue_health, data_quality, extraction_pulse_24h, system_health
  - Uses precomputed `data_quality_snapshots` + `pg_class` estimates for sub-second response
  - Built `/admin/pulse` React page — 60s auto-refresh, green/yellow/red signals, design system compliant
  - Edge function `admin-pulse` deployed

[extraction] Snapshot reextraction queue repopulated
  - Discovered existing `batch-extract-snapshots` v2 + cron jobs for 5 platforms — queue was simply empty
  - Created `repopulate_snapshot_queue()` — finds vehicles with matching snapshots not yet queued
  - Created `cron_repopulate_snapshot_queues()` — runs every 30 min, cycles all platforms
  - Initial run: 23,709 items queued (BJ 9,950 + Mecum 9,950 + Bonhams 3,809)
  - Released 50 stale processing locks

[security] Fixed 5 rate limiting bugs — atomic PG function `check_api_key_rate_limit()`
  - Bug 1: No reset mechanism → auto-resets window when expired (1hr windows)
  - Bug 2: Race condition → FOR UPDATE row lock in PG function (atomic read+decrement)
  - Bug 3: Falsy check → 0 means denied, NULL handled correctly
  - Bug 4: Per-endpoint namespace in IP-based limiter for anonymous requests
  - Bug 5: IP-based rate limiting for anonymous users via `_shared/rateLimit.ts`
  - Bonus: expires_at + scopes enforced atomically, returned in result
  - Created `_shared/apiKeyAuth.ts` shared module (replaces 19 copy-pasted implementations)
  - Updated `api-v1-vehicles/index.ts` as reference implementation
  - Migrated ALL 17 api-v1-* endpoints to shared module (zero files still use old buggy code)
  - Unmigrated by design: api-v1-exchange (no auth), api-v1-business-data (custom return), webhooks-manage
  - Migration applied: `fix_api_key_rate_limiting`

[frontend] Added ESLint design system enforcement plugin
  - Custom plugin: `eslint-plugin-design-system.js` with 5 rules
  - no-hardcoded-colors: catches hex colors in style props (allowlists Recharts/SVG/Leaflet)
  - no-border-radius: zero border-radius enforced
  - no-box-shadow: flat styling enforced
  - no-gradient: no linear/radial/conic gradients
  - no-banned-fonts: only Arial + Courier New allowed
  - Baseline: 2,655 violations (1,618 border-radius, 612 colors, 296 fonts, 104 shadows, 25 gradients)
  - Pre-commit hook updated to report design system violations on staged files
  - All rules set to 'warn' (doesn't break builds, visible to agents)

[feed] Feed quality overhaul — no more boats/motorcycles/farm equipment/aircraft/heavy trucks in default feed
  - feed-query: expanded non-auto make blocklist (80+ makes, case-variant aware), deployed
  - feed-query: dealers hidden from default feed (show when user is searching or toggles dealer filter)
  - MV: rebuilt vehicle_valuation_feed with 0.2x dealer rank penalty + non-auto type/make penalties
  - DB: batch-classified ~12k vehicles (Harley→MOTORCYCLE, Freightliner→BUS, John Deere→HEAVY_EQUIPMENT, etc.)
  - Result: private avg rank 12.77, dealer avg rank 2.67 (was equal before)

[sources] Universal Source Onboarding System — "URL in, vehicles out"
  - Built `onboard-source` edge function: 5-phase pipeline (investigate, profile, census, estimate, monitor)
  - Phase 1: Firecrawl scrape + map, GPT-4o-mini site analysis, writes observation_sources + source_registry + source_intelligence + scrape_sources
  - Phase 2: Auto-creates business profile with name, logo, social links, specializations
  - Phase 3: Census via URL map + browse page parsing, turnover estimation
  - Phase 4: Extraction time estimation based on JS rendering needs, AI overhead
  - Phase 5: Monitoring strategy (sitemap_delta, browse_page_poll, homepage_poll) + coverage targets
  - Poll action for monitoring cron: checks all active sources, diffs URLs, queues new listings
  - Extended `continuous-queue-processor` with dynamic source loading from source_registry (any onboarded source auto-processes)
  - Built `SourcesDashboard.tsx` admin page: add source input, filter tabs, queue stats, source list with completion bars
  - Registered route `/admin/sources` + nav item in AdminShell operations section
  - Created `source-monitor-poll` cron job (every 2h at :30)
  - Fixed source_registry status CHECK constraint to include 'investigating' and 'monitoring'
  - Migration: added onboard_phases_complete, estimated_extraction_hours, monitoring_strategy, monitoring_frequency_hours, observation_source_id to source_registry; estimated_turnover_per_day to source_census
  - End-to-end tested: silodrome.com onboarded through all 5 phases, appears in continuous-queue-processor dynamic sources

[analysis-engine] Analysis Engine v1 — complete data-triggered widget system
  - Created 4 foundation tables: analysis_widgets, analysis_signals, analysis_signal_history, analysis_queue
  - Seeded 14 widget configurations across 6 categories (deal_health, pricing, market, presentation, exposure, timing)
  - Built analysis-engine-coordinator: sweep, compute, evaluate_vehicle, dashboard, acknowledge, dismiss actions
  - Built widget-sell-through-cliff: DOM-based sell-through probability with segment cliff detection
  - Built widget-rerun-decay: multi-listing price decay tracking with VIN-based history
  - Built widget-time-kills-deals: master aggregator combining 7 sub-signals (DOM, engagement, price reductions, seasonal, competition, rerun, exposure)
  - Built widget-completion-discount: deficiency detection + buyer discount calculation with keyword-based cost ranges
  - Built widget-presentation-roi: photo count/quality/description/profile scoring with segment-specific lift benchmarks
  - Built widget-broker-exposure: multi-platform exclusivity erosion tracking (7% per additional platform)
  - Built widget-buyer-qualification: deal jacket buyer readiness scoring (contact, deposit, docs, payment)
  - Built widget-commission-optimizer: price tier benchmarks, margin projection, consignment vs outright analysis
  - Built widget-deal-readiness: 13-item checklist scoring (deal structure, contacts, financial, documents, vehicle)
  - Built widget-geographic-arbitrage: regional price differential analysis across 222+ regions
  - Added inline SQL for 4 widgets: comp-freshness, market-velocity, seasonal-pricing, auction-house-optimizer
  - Created execute_readonly_query RPC for inline SQL widget execution
  - Built api-v1-analysis: authenticated API (GET signals, POST refresh/acknowledge/dismiss, history endpoint)
  - SDK v1.6.0: added nuke.analysis namespace (get, signal, refresh, history, acknowledge, dismiss)
  - Wired observation trigger: ingest-observation fire-and-forgets to coordinator on new observations
  - Claim function (claim_analysis_queue_batch) with FOR UPDATE SKIP LOCKED
  - Pipeline registry entries (9 entries)
  - Cron job 368: sweep every 15 minutes
  - All tested end-to-end: 9 signals returned for test vehicle with health aggregation

## 2026-03-06

[cwtfo] Full situational brief and data integrity audit
  - Discovered 1.3M reported vehicles is ~630K distinct URLs + 157K orphans (39% bloat)
  - BaT: 618K rows → 170K distinct URLs (3.6x duplication, top listing has 445 copies)
  - Cars & Bids: 41K rows, 34K have no URL at all (6.5x bloat)
  - Collecting Cars: 9.6x bloat ratio
  - ConceptCarz: 348K empty shells (0% images/desc/VIN), all created 2026-02-06 in one bulk import with zero provenance
  - Source name splits: "mecum" vs "Mecum", "bat" vs "Bring a Trailer"
  - Extraction yield report per source (deduplicated): BaT 74-79%, Mecum 93-98%, B-J only 19%, Bonhams 9-11%
  - Barrett-Jackson: 69K archived snapshots exist but only 19% of fields extracted — data sitting unprocessed
  - 593K total successful archived snapshots across all platforms
  - Agent task status: 22 pending, 0 running (all sessions crashed, no restarts)
  - Since March 1: only 1 agent task completed, 10+ commits were CSS churn on same page

[cwtfo] Created ConceptCarz investigation prompt for dedicated agent
  - `.claude/prompts/CONCEPTCARZ_INVESTIGATION.md`
  - 3-phase approach: investigate source/overlap/memorabilia → recommend strategy → execute with approval
  - Forces read-only Phase 1 before any data modification

[frontend] Vehicle profile page redesign — layout, contrast, timeline fixes
  - Column widths changed from 55/45 to 30/70 (images-first layout)
  - Hero image increased from 260px to 550px (removed max-height cap, set --h-hero token)
  - Heatmap contrast fixed: overrode --heat-0 to #d4d4d4, --heat-2 to #6ee7b7 in light mode
  - Month/day labels changed from --vp-text-faint (#bbb) to --vp-pencil (#888)
  - Dark mode heatmap: --heat-0 #3a3a3a, --heat-2 #4ade80
  - Timeline receipt popup: position:absolute→fixed with viewport-relative coords, no clipping
  - Receipt clamped to viewport right edge, max-height 60vh with overflow scroll
  - Empty widgets hidden: Timeline gated on timelineEvents.length, Comments on totalCommentCount
  - Layout height tokens (--vp-sticky-top etc) added to light mode block (were dark-only)
  - Files: vehicle-profile.css, WorkspaceContent.tsx, BarcodeTimeline.tsx

[chore] Gitignore scripts/data/ (~1.4GB scraped JSON) and public/data/*.json
[chore] Multi-agent batch commit: map refactor, feed system, wiring harness builder, YONO checkpoint cleanup

[infra] 707 Yucca server planning — iMac renovation for Nuke data server
  - Audited current storage: 13GB nuke project, 151GB YONO cache, 113GB Photos library, 4TB+2TB external drives
  - Assessed 2011-2013 27" iMac at Yucca property for server conversion (Ubuntu Server 24.04)
  - Architecture decided: Ubuntu + Tailscale + MinIO + YONO sidecar + Syncthing on iMac
  - Replaces Modal (YONO sidecar), reduces Supabase egress, centralizes 11 SSD contents
  - Plan: prep "renovation package" HD with CLAUDE.md + setup.sh + configs for Claude-on-iMac to execute
  - M4 Max stays training/dev machine; iMac is storage + always-on services
  - NOT YET BUILT — planning session only, next step is prepping the drive

[feed] Feed ranking v3 — quality gates + score transparency + server-side curation
  - Rebuilt `feed_rank_score` formula in MV (v3): 9 components — deal×recency, heat, for-sale price-tier boost, vehicle-type gating (+8 auto / -40 non-auto), non-auto make blocklist (-35), photo boost (+8), source quality (BaT/C&B +10), location (+2), confidence (+3)
  - Server-side quality gates in `feed-query` edge function: exclude boats/RVs/trailers/motorcycles/farm equipment/aircraft by type AND by make blocklist, $500 minimum price floor
  - `CardRankScore.tsx` — score badge with hover tooltip showing formula decomposition
  - SCORES toggle in FeedToolbar — shows rank scores in all view modes
  - Default sort changed from `newest` → `popular` (feed_rank)
  - Added `canonical_vehicle_type`, `has_photos`, `location/city/state` to feed types and edge function
  - Added `has_images` and `excluded_sources` filter support
  - Deployed and verified: top results are collector vehicles, not trailers/motorhomes

[feed] FB Marketplace saved finds — partial
  - Inserted 4 user-saved FB Marketplace listings into `marketplace_listings`
  - `fb-scrape-saved.ts` switched to `fb-session-1` (session expired, needs manual login)

[analysis] Full Tesla USA auction market analysis — 309 sold vehicles with prices
  - By-model breakdown: Model S (97), Model 3 (102), Model X (53), Model Y (36), Cybertruck (15), Roadster (6)
  - Market curve by year, depreciation curve by age, price distribution, performance premium (-6.4% inverted)
  - Bid velocity: 37 auctions with 1,963 comments, 12 with AI sentiment (avg 0.77, 92% positive)
  - Roadsters dominate engagement (105 comments/auction avg) — becoming collector cars
  - Late surge analysis: 11 auctions with >50% final-quarter comments (bidding war signal)

[data-quality] Vehicle profile quality audit — corrected metrics for the platform
  - 1.29M raw rows → 750K live (540K junk: 504K dupes, 31K deleted, 2.5K rejected, 2K merged)
  - Real tiers: 102K complete (YMM+price+VIN), 280K priced, 678K queryable YMM
  - 504K "duplicates" are BaT comment-scrape artifacts — one row per comment, not per vehicle
  - Plan designed: collapse dupe clusters into observation counts on canonical records, then purge stubs

[prompt] Perplexity research prompt for NL-to-SQL CLI data terminal — prompts/perplexity-cli-data-terminal.md
  - Full real schema: 195 columns, 112 auction sources, 230+ child tables, real row counts
  - 10 example NL queries with expected SQL patterns
  - 5 architecture research questions: NL-to-SQL approach, frameworks, safety, presentation, ambiguity

[map] Smooth zoom/pan — Apple Maps-quality interactions
  - Configured Deck.GL controller: smooth scroll zoom (speed 0.01, smooth: true), inertia (300ms momentum)
  - Added FlyToInterpolator for animated programmatic view transitions (search results fly-to)
  - Replaced bare `controller={true}` with full interaction config (touchZoom, doubleClickZoom, keyboard)

[map] Map v6 UX Overhaul — Phase 3A module extraction + type import fix
  - Extracted mapUtils.ts (353 lines): types, constants, geocoding, hex binning, helpers
  - Extracted hooks/useMapLayers.ts (1024 lines): all Deck.GL layer construction
  - UnifiedMap.tsx reduced from 3,036 → 1,656 lines (-45%)
  - Fixed type-only imports (BizPin, VPin etc.) — Vite strips interfaces, need `import type`
  - Fixed CollapsibleWidget import in ZipSidebarPanel (named export, not default)
  - TypeScript clean, Vite build passes

[data-fix] K10/K20 photo contamination — separated two 1984 Chevrolet trucks
  - Created K20 vehicle record (6ff6497c-784c-4cd7-adcf-28925f97d860, VIN 1GCGK24M6EF375994)
  - Moved 419 misassigned K20 photos from K10 to K20 record
  - Uploaded correct 51 K10 photos from "1984 Chevrolet K10 SWB" album
  - Updated K10 with SPID label data (Scottsdale trim, Frost White, etc.)
  - Hardened iphoto-intake.mjs: added validateVehicleAlbumMatch() — checks year/model match before upload, --force to override

[frontend] Phase 1 — Universal Input System (plan: dreamy-imagining-yao.md)
  - Promoted AIDataIngestionSearch to header (CommandLineLayout.tsx) — replaces plain SearchBar
  - Created GlobalDropZone.tsx — full-page drag-drop overlay, dispatches nuke:global-drop event
  - Wired GlobalDropZone into AppLayout.tsx
  - Added nuke:global-drop listener in AIDataIngestionSearch.tsx (single image → handleImageFile, multi → toast)
  - MobileBottomNav: replaced Market with Inbox, added badge count (orphan vehicle_images query)
  - DomainRoutes: /inbox → PersonalPhotoLibrary, added /photo-library alias, TeamInbox → /team-inbox
  - Build passes clean (TypeScript + Vite)

[yono] Nuke Agent QLoRA fine-tune — Qwen2.5-7B on Modal A100
  - Built training data export script `scripts/export_nuke_agent_data.py`
    - 3 data sources: Supabase schema introspection, edge function code, vehicle domain knowledge
    - Exports chat-format JSONL (system/user/assistant) for instruction tuning
    - 2,049 train + 108 val examples generated
  - Built Modal training script `yono/modal_nuke_agent_train.py`
    - QLoRA (4-bit NF4) on Qwen/Qwen2.5-7B-Instruct
    - LoRA rank=64, alpha=128, 161M trainable params (3.58% of 4.3B)
    - 3 epochs, batch=4, grad_accum=8, cosine LR schedule
    - Includes merge_and_export + list_agent_runs functions
  - Uploaded training data to Modal volume `yono-data`
  - Fixed version compatibility issues:
    - accelerate 0.35 doesn't exist (jumped to 1.0) — removed <1.0 cap
    - transformers 4.57 needs accelerate 1.0+ (keep_torch_compile kwarg)
    - torch_dtype deprecated → dtype
    - Fixed import json ordering bug in main()
  - Training completed: run_id=20260306_144355
    - Loss: 4.35 → 0.07 (rapid convergence), eval_loss=0.0707
    - Runtime: 97 min on A100-SXM4-40GB
    - LoRA adapter saved to volume: nuke-agent-runs/20260306_144355/final/

[data-quality] Massive enrichment campaign — 5 sources running in parallel
  - Barrett-Jackson re_enrich: 3,626+ vehicles enriched, ~1,100 prices + ~2,000 VINs + engine types
  - Bonhams re_enrich: 1,019 vehicles enriched (queue drained), 99.7% success rate
  - Mecum re_enrich: 3,498+ vehicles enriched, ~1,200 VINs added
  - RM Sotheby's: deployed extractor, added offset param, processing 14 auctions
    - PA26 (66 updated), AZ26 (50), CC26 (34), MI26 (20 created + 50 updated), S0226 (6), PA25+ in progress
    - High error rate from memorabilia items (luggage, children's cars) — expected
  - BaT backfill attempted but blocked by "View Result" paywall on ended auctions (21K priceless)
  - Net: +1,000+ prices, +3,000+ VINs (BJ/Mecum still running at session close)

[data-quality] extract-rmsothebys offset support
  - Added `offset` parameter to `process` and `list` actions for batch pagination
  - Allows processing large auctions (190+ lots) within edge function 150s timeout
  - Deployed v2

[scripts] Created scripts/backfill-rmsothebys.sh
  - Processes all 14 known RM auctions in batches of 40
  - Handles offset pagination automatically

[scripts] Created scripts/backfill-bat-prices.sh
  - Feeds BaT URLs to extract-bat-core sequentially
  - NOT effective: BaT paywalls ended auction prices behind "View Result"

[admin] User Metrics Dashboard — /admin/user-metrics
  - New edge function `user-metrics-stats` — 11 parallel SQL queries across bat_user_profiles (504K), bat_users (1.2K), ghost_users (156), fb_marketplace_sellers (127), external_identities (509K), profiles (6)
  - New admin page with stat cards, linkage progress bars, BaT comment distribution chart (Recharts), top 25 users table, ghost/FB/platform breakdowns
  - Route registered at /admin/user-metrics, nav link in Operations section of AdminShell
  - Edge function deployed and live

## 2026-03-05 (Data Source Landscape & Gap Filling)

[data-quality] Deep research on ConceptCarz business model & pricing methodology
  - Proved CZ is an ad-supported content farm (~3 person operation since 1998)
  - "Estimated Sale Value" = trimmed mean of all auctions for a model, NOT a transaction price
  - "Condition tiers" (Fair/Good/Excellent/Perfect) are just price quartiles, not real condition assessments
  - Positioned like KBB/Hagerty but without the rigor — no physical inspections, no defined criteria
  - Full investigation documented in conceptcarz_investigation.md

[data-quality] Comprehensive auction data source landscape analysis
  - Mapped 30+ sources across 5 tiers: Primary Auctions, Aggregators, Expert Valuations, Marketplaces, Wholesale
  - Defined trust tier taxonomy: transaction > aggregated_transaction > expert_valuation > asking_price > computed_estimate
  - Identified Classic.com, Glenmarch, Sports Car Market, Hagerty API as priority ingestion targets
  - Assessed every source for data quality, accessibility, coverage, and known issues

[data-quality] Merged 46,912 duplicate vehicle stubs
  - Found ~45K rows where listing_url matched another vehicle's discovery_url (same car, two records)
  - 98.8% of duplicates had price already on the canonical vehicle
  - BaT: 23,712 merged | BJ: 21,079 | C&B: 50 | Others: 71
  - Used status='merged' + merged_into_vehicle_id to preserve lineage

[data-quality] Barrett-Jackson VIN backfill via re_enrich
  - Backfilled discovery_url for ~760 BJ rows (enabling extractor to find them)
  - Ran re_enrich: 2,397 BJ vehicles enriched, 4,895 VINs added (+33%)
  - Confirmed prices being extracted ($140K Auburn, $2.4M Mercedes 540K, etc.)

[data-quality] Fixed get_enrichment_candidates RPC
  - Was missing sale_price IS NULL from enrichment criteria
  - Bonhams, Gooding, etc. couldn't find price-missing vehicles
  - Updated to include sale_price in enrichment eligibility

[data-quality] Bonhams extractor re_enrich query fix
  - Fallback query had .is("year", null) — filtered out all records that already had year
  - Changed to .or("year.is.null,sale_price.is.null,description.is.null")
  - Deployed extract-bonhams with fix

[scripts] Created backfill-auction-prices.sh
  - Loops re_enrich calls for BJ/Bonhams/Mecum extractors
  - Configurable batch size, concurrency, sleep between rounds

[scripts] Created merge-duplicate-stubs.sh
  - Identifies and merges duplicate vehicle stubs across all auction sources
  - Uses SET session_replication_role = replica to bypass triggers

## 2026-03-04 (Wiring Harness Builder — Full Implementation)

[wiring] Complete visual harness builder for vehicle wiring layouts
  - DB migration: 6 new tables (harness_designs, harness_sections, harness_endpoints, harness_templates, electrical_system_catalog, motec_pin_maps)
  - Seeded: 46 electrical systems, 104 MoTeC pin maps (M130/PDM30/C125), 1 Barton invoice template
  - Extended wiring_connections with 13 new columns (from/to endpoint IDs, calculated gauge, voltage drop, fuse rating, etc.)
  - TypeScript types, AWG resistance table, wire color standards, voltage drop calculations, gauge selection algorithm
  - SVG canvas with pan/zoom, foreignObject HTML nodes (Win95 design), cubic bezier wire edges
  - useReducer state management with undo-capable actions
  - Debounced persistence (800ms canvas state, immediate structural changes)
  - Right sidebar: node editor (name/type/amps/connector/location) + connection editor (color/gauge/length/fuse)
  - Bottom load summary bar: total amps, alternator sizing, battery sizing, PDM channels, warnings
  - Left systems palette: 46 catalog items grouped by category, click-to-add, green/red/grey status indicators
  - Completeness panel: % score, missing required/optional items, +ADD buttons, build intent filtering
  - Toolbar: SELECT/WIRE modes, +ENDPOINT, DELETE, zoom controls, CHECK completeness toggle
  - Keyboard shortcuts: V=select, W=wire, Delete=remove, Escape=deselect
  - Auto-calculations on wire draw: gauge selection, wire color suggestion, length estimation, fuse rating
  - WiringPlan.tsx: template picker, lazy-loaded builder, AI assistant tab preserved
  - Files: harnessTypes.ts, harnessConstants.ts, harnessCalculations.ts, useHarnessState.ts, HarnessCanvas.tsx, HarnessCanvasNode.tsx, HarnessCanvasEdge.tsx, HarnessCanvasSectionGroup.tsx, HarnessToolbar.tsx, HarnessBuilder.tsx, HarnessSidebar.tsx, HarnessLoadSummary.tsx, HarnessSystemsPalette.tsx, HarnessCompletenessPanel.tsx, WiringPlan.tsx
  - Zero TypeScript errors, zero new npm dependencies

## 2026-03-02 (session 3 — save-all + enrichment continued)

[data] Collecting Cars: Downloaded 18,037 lots from Typesense API (17,685 sold + 157 live + 195 coming soon)
  - Saved to scripts/data/collecting-cars/{sold,live,comingsoon}.json
  - Enrichment: 452 matched by slug, +212 GPS fixes (48.3% → 49.4%)
  - Fixed matching to use coords field from Typesense + fuzzy slug matching (base without -N suffix)
  - CC Typesense data has precise coords [lat,lon] for all 18,037 lots

[data] Craigslist: +206 vehicles geocoded from 120 new subdomain→GPS mappings (39.1% → 41.8%)
  - Built comprehensive CL subdomain → GPS map (abbotsford through youngstown)
  - Remaining 2 with null subdomains are dead ends

[data] Facebook Marketplace: +120 vehicles geocoded from city name matching (25.3% → 27.0%)
  - Built "City, ST" → GPS lookup for 100+ US cities
  - Remaining 420 are small towns (2-3 each), would need Nominatim or similar

[data] BaT API enrichment from 277 cached pages: 1,940 vehicles updated (price/title/date)
  - BaT API confirmed: lat/lon fields are ALWAYS null — no GPS from API
  - BaT rate-limiting blocks crawl after ~277 pages (429 errors)
  - 9,972 listings cached in scripts/data/bat-api-pages/

[data] BaT snapshots: 375,351 HTML snapshots available but NO location data in HTML
  - Location data is dynamically loaded, not in the archived HTML

[data] Investigation findings (no GPS gains possible):
  - Gooding: 5,892 vehicles without URLs are historical imports (no URL, no location, no auction info)
  - PCarMarket: 5,839 vehicles without any location — would require scraping individual listing pages
  - Cars & Bids: Online-only auction, no location data exists
  - Barrett-Jackson price: API blocked by Cloudflare WAF (needs residential proxy)

[data] Overall GPS: 282,184 / 746,371 (37.8%)

## 2026-03-02 (session 2 — save-all data caching sprint)

[data] Save-all data caching + enrichment sprint — +37K more vehicles geocoded, 302K Mecum lots saved
  - Mecum Algolia: Downloaded ALL 302,223 lots from Algolia search index (263 auction events, 1.2GB saved to scripts/data/mecum-algolia/)
  - Mecum URL enrichment: 28,169 vehicles matched by URL, 27,855 updated (title, make, model, year)
  - Mecum year+make+price matching: +16,631 GPS fixes for URL-less vehicles, +16,631 listing URLs added (38.5% → 58.9% GPS)
  - Bonhams: Fetched 899 auction locations from bonhams.com/auction/ pages, saved to scripts/data/bonhams-auction-locations.json
  - Bonhams: +18,184 vehicles geocoded from auction→city mapping (0% → 72.2% GPS)
  - Gooding: Downloaded 2,174 lots from Gatsby page-data API, saved to scripts/data/gooding-lots/
  - Gooding: +1,877 GPS fixes from auction event names (0.9% → 24.2% GPS)
  - Broad Arrow: URL-based geocoding (12 event codes mapped) → +1,738 vehicles (0.8% → 88.8% GPS)
  - Scripts created: mecum-algolia-save-all.cjs, bonhams-auction-geocode.cjs, gooding-save-all.cjs, collecting-cars-save-all.cjs
  - BaT API rate-limited after 277 pages (9,972 listings)
  - Overall GPS: 244,741 (32.8%) → 282,184 (37.8%) = +37,443 across 2 sessions

## 2026-03-02

[data] Mass geocoding sprint — +41K vehicles geocoded
  - Barrett-Jackson: URL-based geocoding (9 event cities from URL slugs) → 33,918 vehicles (48% → 99.6% GPS)
  - Craigslist: subdomain-based geocoding (50+ metros) → 2,782 vehicles
  - RM Sotheby's: event code geocoding (az/mo/pa/mi → Scottsdale/Monterey/Paris/Milan) → 961 vehicles
  - GAA Classic Cars: single-location (Greensboro, NC) → 1,294 vehicles
  - Beverly Hills Car Club: single-location (Los Angeles, CA) → 1,998 vehicles
  - Gooding: snapshot-based geocoding (Pebble Beach/Scottsdale/Amelia Island) → 63 vehicles
  - SBX Cars, Collective Auto, Volo Cars: single-location → 356 vehicles
  - Mecum geocoding function updated with Schaumburg, cron slowed to hourly (exhausted)
  - Overall GPS: 201K (27.0%) → 241K+ (32.3%)
[data] Source name consolidation
  - facebook_marketplace + Facebook Marketplace → facebook-marketplace (3,753 unified)
  - Broad Arrow → broad_arrow, RM Sothebys → rm-sothebys, barrettjackson → barrett-jackson
  - classic_com + Classic.com → classic-com
[data] Barrett-Jackson API discovery
  - Found REST API at /api/previous-docket-results (prices, VINs, descriptions, 84 events, ~55K lots)
  - Also /api/facets (event list), /api/docket (active auctions)
  - BLOCKED: Cloudflare WAF, datacenter IPs rejected (same as FB Marketplace)
  - Script written: scripts/bj-api-save-all.cjs (needs residential proxy)
[data] BaT API save-all running overnight
  - scripts/bat-api-save-all.cjs saving all 6,442 pages to scripts/data/bat-api-pages/
  - 231K listings with price, GPS, title, noreserve — permanent local cache
  - Running at ~15 pages/min, ~7hr total
[data] SQL geocoding functions created:
  - geocode_bj_from_urls(batch_size) — B-J URL slug → 9 cities
  - geocode_gooding_from_snapshots(batch_size) — Gooding HTML → 6 cities
  - geocode_mecum_from_snapshots updated with Schaumburg

[frontend] V3 Vehicle Profile Redesign — badge variants CSS, barcode timeline component, badge bar component, gallery column slider, all widgets variant="profile", overscroll-behavior fix, dense info table CSS, page-level typography
[stbarth] Modal GPU vision OCR server deployed and running
  - `scripts/stbarth/modal_vision_server.py` — Qwen2.5-VL-7B-Instruct-AWQ on A10G via vLLM
  - Ollama-compatible API at https://sss97133--stbarth-vision-ocr-web.modal.run
  - AWQ quantization (4-bit) fits comfortably on 22GB A10G VRAM
  - vLLM 0.8.3 + transformers 4.57.x + rope_scaling patch
  - Production throughput: ~1,800 pages/hr @ concurrency 8
  - Projected cost: ~$31 for all 41K pages (vs $414 for Haiku API)
  - 1,000+ pages completed in initial runs, 48 permanently failed (403 CDN)
[data] organization_locations table — multi-location support for orgs
  - 4,593 rows backfilled from organizations table (4,589 primary + 5 Epstein metadata locations)
  - location_id FK added to organization_vehicles
  - Epstein Collection: 5 locations (LSJ, NYC, Palm Beach, NM, Paris), 32/38 vehicles linked
  - search_organizations_near() PostGIS RPC deployed — proximity search working
  - geocode-organization-locations edge function deployed — two-pass (lookup table + Nominatim)
  - Geocoding COMPLETE: 4,308/4,593 locations geocoded (93.8%)
    - 3,205 via Nominatim, 971 imported, 120 lookup table, 12 manual
    - 285 remaining have no city data (can't geocode)
    - Fixed cron job (invalid JSON body), added COUNTRY_CODE map (30+ countries),
      JUNK_CITIES filter, COUNTRY_NAME_FALLBACK for small territories
    - Cleaned 136+ junk city entries (2-char codes, "Exclusive Car Registry", "Homepage", etc.)
    - Bulk strategy: Python batch geocoder + SQL cross-matching + lookup table bulk update
    - Cron #364 disabled (complete)
[data] Epstein Collection provenance completed — 93/93 field provenance rows (38 make + 33 model + 22 year)
[data] FB Marketplace data quality cleanup
  - 299 junk records rejected (motorcycles, boats, ATVs, snowmobiles, jet skis, empty listings)
  - import-fb-marketplace filter expanded: Honda moto models (CB, CBR, Shadow, Goldwing, Magna, etc.),
    BMW moto models (R-series GS, S1000, G310), Suzuki (Burgman, V-Strom), Triumph (Bonneville, Tiger),
    generic keywords (motorcycle, sport bike, chopper, bobber, pontoon)
  - False-positive-safe: scoped rebel/valkyrie to Honda, bonneville/tiger to Triumph, k/c-series to BMW,
    gs/sv/dr-series to Suzuki. Protects AMC Rebel, Pontiac Bonneville, Sunbeam Tiger, Aston Martin Valkyrie,
    Buick GS, Lexus GS, Chevy K-trucks, Mercedes C-class
  - 912 make names case-normalized (ford→Ford, chevrolet→Chevrolet, etc.)
  - 176 additional non-vehicle junk rejected (boats, planes, golf carts, snowmobiles)
  - Added MAKE_CANONICAL normalization map to import function (prevents future case issues)
  - Final state: 3,296 clean FB vehicles, 1,929 rejected (37% rejection rate)

[search] Smart search RPCs deployed — "porsche" now returns 78,221 results (was 7)
  - search_vehicles_browse: 17-param filtered browse with dynamic SQL, COUNT(*) OVER() totals
  - search_vehicles_smart: 4-strategy cascade (exact make → make+model → FTS → trigram)
  - search_autocomplete: categorized results (makes, models, vehicles)
  - search_market_data: JSONB with median price, distribution, recent sales
  - browse_stats: JSONB with total, with_images, with_price, avg_price, by_source/era/model
  - Fixed sold_price type mismatch (INT not NUMERIC)
[search] Intent router + query parser (src/lib/search/)
  - 8 intent modes: NAVIGATE, EXACT_VIN, EXACT_URL, MY_VEHICLES, MARKET, QUESTION, BROWSE, QUERY
  - Query parser extracts: year, price, make, model, body style, color, era
  - 34 unit tests passing (19 intent + 15 parser)
  - Dictionaries: 54 makes, 18 aliases, 22 body styles, 12 eras (mapped to DB values), 27 colors, 15 domains
[header] 4 switchable header variants (command-line, segmented, two-row, minimal)
  - HeaderVariant type + localStorage persistence in ThemeContext
  - Zero-prop AppHeader orchestrator with variant delegation
  - Shared sub-components: SearchBar, SearchOverlay, UserArea, UserDropdown, NavLinks
  - SearchBar: ghost placeholder rotation, ⌘K hint, 4 modes (inline/expanding/compact/trigger)
  - SearchOverlay: recent items + categorized autocomplete + keyboard hints
  - UserDropdown: merged NukeMenu + profile dropdown, header variant picker
  - Responsive: mobile collapses all variants to [NUKE] [⌘K] [avatar]
  - Deleted NukeMenu.tsx and SearchSlot.tsx
[header] AppHeader.css — complete grid layouts for all 4 variants + responsive breakpoints
[design] --radius: 0px global change in unified-design-system.css
[browse] BrowseVehicles page — stats bar, model pills, sort/filter, images toggle, pagination
[db] 4 new indexes (make_status, make_source, make_sold_price, era)
[db] user_vehicle_links table with RLS
[settings] Header variant selector added to AppearanceSpecimen (Capsule settings)

## 2026-03-01

[fb-marketplace] Scraper v3.1 — added --group N flag to split 58 cities into 4 groups of ~15
  - Softer rate limiting: skip-and-continue instead of global abort (3 consecutive = abort)
  - 30s extra delay after rate-limited city (was: instant abort)
  - Counter resets on any successful city scrape
[fb-marketplace] Replaced single daily LaunchAgent with 4 staggered group sweeps (3am/9am/3pm/9pm)
  - com.nuke.fb-sweep.plist → com.nuke.fb-sweep-g{1,2,3,4}.plist
  - Each group: --all --group N --max-pages 25 (was: --all --max-pages 50)
  - 6-hour spacing gives FB rate limit full recovery window
[fb-marketplace] Created monitor-fb-marketplace edge function — 5 health checks
  - Sweep freshness (24h), unlinked backlog (500), error rate (50%), data freshness (48h), refine backlog (1000)
  - Creates admin_notifications on threshold breach, 6h dedup
[fb-marketplace] Added 3 pg_cron jobs:
  - fb-marketplace-import: */30 * * * * — converts unlinked listings to vehicles (batch_size=50)
  - fb-marketplace-refine: 15,45 * * * * — enriches via bingbot HTML (batch_size=15)
  - fb-marketplace-monitor: 0 */6 * * * — health checks + alerting
[fb-marketplace] Deployed import-fb-marketplace and refine-fb-listing edge functions (were local-only)
  - First import batch: 38 vehicles created from 50 listings, 12 blocked (non-cars)
  - Backlog: 2,810 unlinked → will clear in ~14 hours via cron

## 2026-03-01 (Overnight Autonomous Session)

[git] Committed and pushed 330 files of accumulated multi-agent work (e98d0cb85)
[frontend] Fixed 7 crash bugs: Rules of Hooks violation, null guards, SSR safety, infinite loop, undefined text
[frontend] Search results + vehicle cards now show image/event counts and deal score badges
[db] Backfilled 61,385 vehicles with primary_image_url from vehicle_images
[db] Data quality scoring: 37% → 99.94% coverage (1.25M vehicles scored in ~15 minutes)
[db] VIN varchar overflow fix in vehicle_mailboxes (widened to varchar(50))
[infra] Deployed 22 edge functions (14 updated, 8 new including agent hierarchy)
[infra] Cron audit: fixed 3 broken jobs + 1 security fix (hardcoded key), cleaned 51K stale log rows
[infra] Agent hierarchy wired to crons: router (5min), haiku worker (2min), sonnet supervisor (10min)
[extraction] Snapshot extraction fixes: Craigslist archiveFetch, Bonhams JSON-LD fallback, Barrett-Jackson Cloudflare detection, Cars & Bids retry
[extraction] Import queue: 170 → 146 failed items, VIN overflow fixed, Firecrawl items skipped
[search] Universal search accepts both ?q= and ?query= parameters
[sdk] @nuke1/sdk v1.5.0 README updated to match actual vision types, LICENSE file added
[fb] National FB Marketplace sweep running (58 metros, ~1000+ vintage listings so far)
[yono] Verified YONO sidecar healthy (2 warm containers, all tier-2 families loaded)

## 2026-03-01 (Mass Snapshot Extraction v2)

[extraction] Created snapshot_extraction_queue table with pre-computed vehicle→snapshot matches
  - Pre-joined vehicles to listing_page_snapshots with URL normalization (trailing slashes, case)
  - Queue populated: BaT 283K, B-J 23K, Mecum 16K, C&B 1.7K, Bonhams 855 = 326K total
  - Atomic claim_extraction_batch() RPC for lock-free parallel processing

[extraction] Added queue mode to batch-extract-snapshots v2
  - `use_queue: true` — claims from pre-computed queue instead of OFFSET scanning
  - Eliminates statement timeouts at high offsets (40 workers was crashing DB)
  - 100% snapshot hit rate (0 noSnapshot) vs ~40-50% in legacy mode

[extraction] Fixed C&B URL case-sensitivity — snapshot URLs have different case than vehicle URLs
  - Added lowercase URL variants for carsandbids platform matching

[extraction] Completed C&B extraction: 1,728 vehicles → 17,409 fields filled (~10 fields/vehicle)
  - Color +1,389, Transmission +1,387, Engine +1,037, Description +1,393

[extraction] Completed Bonhams extraction: 855 vehicles → 139 fields filled

[extraction] BaT extraction running: 15K+ of 284K processed so far → 38K+ fields filled
  - Color +6,518, Transmission +13,373, Engine +8,834, Description +5,764, Mileage +12,842
  - 5 workers running in background, ~268K remaining (~13h estimated)

[extraction] Barrett-Jackson: 23K queued but CSR shells produce 0 extractable fields
  - Need Playwright/API approach for VIN, colors, engine data

## 2026-03-01

[quality] Massively accelerated data_quality_score backfill — scored 790K+ vehicles in ~15 minutes
  - Created `quality_backfill_shard(shard_index, total_shards, batch_limit)` function with UUID-prefix isolation
  - Ran 4 parallel shards (5000 rows each, every 3 minutes) to eliminate deadlocks
  - Result: 99.94% vehicles scored (1,256,107/1,256,922), avg score 75.58
  - Remaining 815 zero-score vehicles are genuinely empty (no year/make/model/anything)
  - Disabled old `data-quality-workforce` cron (job 304, 300/run) — replaced with:
    - `quality-score-maintenance` (job 343): `*/5 * * * *`, 1000/run — handles new incoming vehicles
  - Removed temporary aggressive shards (jobs 339-342) after backfill completed
  - Created `fast_backfill_quality_scores(batch_limit)` function — inline scoring with `session_replication_role=replica` (bypasses 29 triggers)
  - Ran additional sweep: 800K rows in 19m via management API, 10K rows/batch, ~500-690 rows/sec
  - Replaced old inactive cron (job 237, 50 rows/5min) with `quality-backfill-fast` (job 344, 5000 rows/10min)
  - Final state: 1,241,306 scored / 1,242,120 total (99.93%), 814 genuinely empty, 0 nulls
[snapshots] Fixed snapshot success rates for Bonhams, Barrett-Jackson, Cars & Bids, Craigslist
  - archiveFetch: Added isGarbageHtml() to detect Cloudflare challenges, React shells, and bot walls — marks as success=false instead of true
  - Craigslist: Replaced raw fetch() with archiveFetch() in extract-craigslist, process-cl-queue, scrape-all-craigslist-squarebodies — was creating 0 snapshots
  - Craigslist: Removed bot User-Agent that Craigslist blocks, now uses browser UAs via hybridFetcher
  - Bonhams: Added JSON-LD fallback when Firecrawl fails/credits exhausted — gets year/make/model/price from React shell
  - Bonhams: Wrapped Firecrawl call in try/catch so credits exhaustion doesn't crash the extractor
  - Barrett-Jackson: Added 503 and Cloudflare JS challenge detection to skip useless direct fetches faster
  - Cars & Bids: Increased Firecrawl maxAttempts from 1 to 2 (retry once on transient failure)
  - Cars & Bids: Added missing fetched_at timestamp to snapshot records

[agent-hierarchy] Wired agent hierarchy into pg_cron for continuous processing
  - agent-tier-router-pipeline (job 336): every 5 min, runs full Haiku dispatch + Sonnet review cycle (10 items/batch)
  - haiku-extraction-worker (job 337): every 2 min, additional Haiku extraction capacity (10 items/batch)
  - sonnet-supervisor-review (job 338): every 10 min, additional Sonnet review for pending_review items (10 items/batch)
  - All three functions tested manually — healthy and processing correctly
  - 460 pending items in import_queue at deploy time
  - Migration: 20260301010000_agent_hierarchy_crons.sql
  - Enables 10x cheaper extraction via Haiku ($1/$5 MTok) vs Sonnet ($3/$15 MTok)

## 2026-02-28 (Photo Spatial Mapping — 10K GPS Pins)
- [scripts] iphoto-intake.mjs: Added `--map-only` mode — inserts GPS metadata from osxphotos without requiring local image files (works with iCloud-only photos)
- [scripts] iphoto-intake.mjs: `queryAlbumMetadata()` extracts lat/lng/place/date/EXIF from osxphotos JSON, `extractPhotoMeta()` handles nested place objects
- [scripts] iphoto-intake.mjs: `--backfill-gps` mode updates existing iphoto images with GPS from Apple Photos metadata
- [scripts] Ran `--map-only` across all 72 vehicle albums: 10,181 GPS-tagged photos across 48 vehicles
- [frontend] UnifiedMap.tsx: Photo map layer (magenta pins) with GPS-tagged images as ScatterplotLayer
- [frontend] UnifiedMap.tsx: Photo side panel with thumbnail, vehicle link, location, date, camera, GPS coords
- [frontend] UnifiedMap.tsx: Increased photo layer limit 5K→15K to display full dataset
- [data] Before: 0% of iphoto images had GPS. After: 99.6% (10,181/10,219) have GPS coordinates

## 2026-02-28 (Vehicle Zone Deprecation / Angle String Migration)
- [frontend] NEW: `nuke_frontend/src/constants/vehicleZones.ts` -- canonical 41-zone taxonomy constants (ZONE_CATEGORIES, ZONE_LABELS, ZONE_DISPLAY_PRIORITY, ESSENTIAL_ZONES, ANGLE_TO_ZONE_MAP, ANGLE_FAMILY_TO_ZONE_MAP, helper functions)
- [frontend] REWRITE: `imageDisplayPriority.ts` -- scoring now driven by `vehicle_zone` + `zone_confidence` + `photo_quality_score` from YONO; legacy angle fallback preserved but marked DEPRECATED
- [frontend] REWRITE: `imageCoverageTracker.ts` -- coverage analysis now uses `vehicle_zone` column directly; essential zones from constants; legacy `getEssentialAngles()` kept as deprecated alias
- [frontend] UPDATE: `imageFilterUtils.ts` `scoreMoneyShot()` -- prefers `vehicle_zone` for scoring, falls back to legacy `ai_detected_angle`/`angle` strings; function-level deprecation docstring
- [frontend] DEPRECATION COMMENTS: `imageAngleService.ts` (module-level + per-function), `personalPhotoLibraryService.ts` (angle_breakdown type), `vehicleFieldScoring.ts` (engine_bay reference), `ImageGallery.tsx` (catPriority maps), `About.tsx` (schema diagram updated)
- [backend] DEPRECATION COMMENTS: `process-all-images-cron/index.ts`, `analyze-image/index.ts`, `analyze-image/coordinate_output.ts`, `import-classiccars-listing/index.ts` -- all marked as using legacy angle strings, pointing to vehicle_zone system

## 2026-02-28 (Image Gallery Zone View)
- [frontend] ImageZoneSection.tsx: New collapsible zone-grouped gallery component (HIGHLIGHTS/EXTERIOR/ENGINE BAY/INTERIOR/UNDERCARRIAGE/WHEELS/DETAIL/DOCUMENTS/UNCATEGORIZED)
- [frontend] ImageGallery.tsx: Added "Zones" as DEFAULT view mode (before Grid/Full/Info/Sessions), surfaces vehicle_zone, photo_quality_score, condition_score, damage_flags from YONO pipeline
- [frontend] Zone sections sort by photo_quality_score DESC, show condition badge + damage dot + photo quality indicator on thumbnails

## 2026-02-28 (First-Touch User Engagement Overhaul)
- [frontend] Homepage: Live vehicle showcase strip (8 real vehicles with images, auto-refresh 60s)
- [frontend] Homepage: Inline search preview dropdown (debounced 300ms, 5 results)
- [frontend] Homepage: "Take a Tour" button wired to OnboardingSlideshow
- [frontend] OnboardingSlideshow: Trimmed 5→3 slides, emoji→ASCII art, renamed "HOW IT WORKS"
- [frontend] VehicleCardDense: No-image fallback → text-based identity card (year/make/model + data points)
- [frontend] CursorHomepage: First-visit context banner (dismissible, localStorage-persisted)
- [frontend] Login/Signup: Added "WHY SIGN UP" value proposition column for signup mode
- [docs] Created FIRST_TOUCH_FIX_MAP.md (audit) and FIRST_TOUCH_REPORT.md (implementation report)

## 2026-02-28 (Theme System Audit & Fix)
- [frontend] Phase 1-2: Full theme audit — found 1,709 inline violations, 97 undefined CSS vars, 3 CSS files broken
- [frontend] Phase 3: Added ~90 new CSS variables to unified-design-system.css (both light/dark blocks)
- [frontend] Phase 3: Fixed 80+ TSX files (~800+ hardcoded colors → CSS variables)
- [frontend] Phase 3: Fixed 3 CSS files (AnnotatedField, ProfessionalToolbox, MergeProposalsDashboard) — zero violations
- [frontend] Phase 4: Updated index.css compat layer with audit stats and documentation
- [frontend] Phase 6: Wrote THEME_AUDIT_REPORT.md — full stats, remaining debt, recommendations
- [frontend] Phase 3 cont: Fixed 170+ more TSX files across 5 batch sweeps (~2,000+ additional fixes)
- [frontend] Batches covered: top 20 offenders, next 16, 9 mid-tier, 20 more, then full 107-file sweep of all remaining
- [frontend] Result: 89% reduction in inline violations (1,709→185), 99.2% of genuine bare colors eliminated (1,709→13)
- [frontend] Remaining 185 refs: 101 intentional (dark overlays, maps), 53 correct var(--token, #fallback), ~13 genuine (brand colors, Three.js, Recharts)
- [frontend] Updated THEME_AUDIT_REPORT.md with final statistics

## 2026-02-28 (Automated Labor Estimation Pipeline)
- [labor] Phase 1: YONO fabrication stage head — 10-stage taxonomy (raw→complete), auto_label_stages.py, train_stage_classifier.py, StageClassifier in server.py
- [labor] Phase 2: Auto work session detection — detect_work_sessions() SQL + auto-detect-sessions edge function
- [labor] Phase 3: Delta-to-labor mapping — stage_transition_labor_map (15 seed transitions), estimate_labor_from_delta() SQL, compute-labor-estimate edge function
- [labor] Phase 4: Unarchived detect-before-after, replaced OpenAI GPT-4O with callTierVision (Sonnet)
- [labor] Phase 5: YONO active learning — yono-escalation-router (confidence tiers), yono_training_queue, yono-export-training, retrain_from_queue.py
- [labor] Phase 6: Photo coaching — photoCoaching.ts, wired into sms-work-intake + sms-reminder-scheduler (photo_gap_nudge)
- [labor] Phase 7: Full pipeline wiring — progress_shot → yono-analyze → escalation → sessions → before/after → labor estimate → coaching
- [labor] DB: fabrication_stage/stage_confidence columns, work_sessions/labor_estimates extensions, stage_transition_labor_map, yono_training_queue
- [labor] 9 edge functions deployed: auto-detect-sessions, compute-labor-estimate, detect-before-after, yono-escalation-router, yono-export-training, yono-analyze (updated), photo-pipeline-orchestrator (updated), sms-work-intake (updated), sms-reminder-scheduler (updated)

### [VP Extraction] P0: Fix Cars & Bids extraction pipeline — 2026-02-27 21:30 UTC
**Task ID:** 200cba73-c5b7-4cc5-a5a2-4a77791ffe62 (RESOLVED)

**Problem:** 488 C&B vehicles created in last 7 days had 0 comments, 0 bids, 0 listing URLs. Root cause: `extract-premium-auction` called `extract-cars-and-bids-core` (core data only) but never triggered secondary extractors (`extract-cars-and-bids-comments` and `extract-cab-bids`).

**Solution:**
1. **Modified `extract-premium-auction`**: Added non-blocking triggers for comment and bid extraction after successful core extraction (both index page and individual listing modes)
2. **Updated `continuous-queue-processor`**: Added C&B comment/bid extraction triggers (same pattern as BaT)
3. **Created `backfill-cb-extraction`**: New edge function to re-trigger full extraction for existing 489 C&B vehicles
4. **Backfill execution**: Successfully triggered 489 extraction jobs (verified via function response)

**Files changed:**
- `supabase/functions/extract-premium-auction/index.ts`: Added C&B comment/bid fetch triggers (lines 118-153 for index, 184-219 for individual)
- `supabase/functions/continuous-queue-processor/index.ts`: Added C&B secondary extraction block (lines 433-464)
- `supabase/functions/backfill-cb-extraction/index.ts`: New backfill function (88.62kB)

**Deployment:**
- `extract-premium-auction` deployed ✓
- `continuous-queue-processor` deployed ✓
- `backfill-cb-extraction` deployed ✓
- Backfill executed: 489/489 vehicles processed

**Impact:** C&B vehicles now receive complete extraction pipeline:
- Core data (VIN, specs, images, descriptions) via `extract-cars-and-bids-core`
- All auction comments via `extract-cars-and-bids-comments`
- Full bid history via `extract-cab-bids`

**Commit:** 33eedb043

### [frontend] Competitors page reframed to partner ecosystem — 2026-02-27
- Rewrote MarketCompetitors.tsx — changed framing from adversarial competitor comparison to partnership ecosystem
- Removed: NUKE_ADVANTAGES attack section, "vs. X" summary cards, Nuke as a peer card in competitor grid, red ✗ scoring
- Added: Partnership model callout (partners bring inventory/regulation, Nuke brings data/pricing/distribution)
- Added: Per-platform "What they have" + "Partnership opportunity" sections
- Added: Capability map showing complementary strengths (green ✓ only, no negative scoring)
- Added: "What Nuke Brings to Partners" (Data API, Comps engine, Vision AI, Investor distribution)
- Added: Integration Paths section (Data API / Vision AI / Listing Distribution / Co-branded Pricing Badge)
- Added: Market opportunity stats block ($37-43B market, <$100M fractionalized, <0.3%)
- CTA now includes B2B platform partnership inquiry (mailto) alongside investor CTA
- Task ca84c465 completed

### [frontend] Exchange SQBD page — show actual vehicle holdings — 2026-02-27
- Added Fund Holdings section to MarketFundDetail.tsx
- Queries top 12 vehicles by sale price matching segment criteria (makes, year range, model keywords)
- Displays vehicle cards with photo, year/make/model, and verified auction sale price
- Animated skeleton while loading, graceful empty state if no matches
- Clicking any card navigates to vehicle profile page
- Works for all funds/segments, not just SQBD

### [frontend] Remove Share This Page copy-link box — 2026-02-27
- Deleted "Share this page:" bordered box (label + URL code + "Copy link" button) from MarketCompetitors.tsx
- Removed "Share link" button from MarketCompetitors.tsx header
- Removed `handleShare` function and `copied` state from MarketCompetitors.tsx
- Removed Share button + `copyLink` function + `copied` state + `copyBtn` style from VehiclePortfolio.tsx
- OG meta tags in MarketCompetitors.tsx useEffect preserved (not UI clutter)

### [frontend] Replace hardcoded homepage stats with live DB queries — 2026-02-27
- `useLandingStats` now fetches `totalImages` via `vehicle_images` estimated count (~34.2M actual vs hardcoded 33M+)
- Hero stat panel: "33M+" photos replaced with live `formatNum(totalImages)` (shows "—" loading, then live)
- API feature card: "18K+" vehicles replaced with live `formatNum(totalVehicles)` (~1M actual)
- `InvestorOffering.tsx`: static YONO text updated from "33M+" to "34M+" to match actual data
- Commit: 2f1f6e1eb, pushed to main

### [frontend] Fix Photos & History tab colors for light/dark mode — 2026-02-27
- Replaced hardcoded white/dark-only colors in `WorkspaceTabBar.tsx` with theme-aware CSS variables
- Background: `var(--grey-800)` → `var(--surface)`, borders: `var(--grey-700)` → `var(--border)`
- Text: `#fff` / `rgba(255,255,255,...)` → `var(--text)` / `var(--text-muted)`
- Active indicator: `#fff` → `var(--text)`, active bg: hardcoded → `var(--surface-hover)`
- Follows DynamicTabBar pattern — works correctly in both light and dark themes

### [frontend] Remove Ready to Trade + Investor Inquiry CTAs — 2026-02-27
- Removed both CTA sections from `MarketCompetitors.tsx` (lines 554-599)
- "Ready to trade?" (Exchange/Portfolio buttons) and "Investor inquiry?" (Data Room/Email buttons) both gone
- `navigate` still used elsewhere in file — no dead import cleanup needed

### [CWTFO] Work Order Lifecycle — Full Data Layer + Auto-Ordering — 2026-02-27
- Invoice HTML for 1983 GMC K2500 Granholm (INV-K2500-0227-001, $1,319.92)
- Vehicle created in DB (3629e106), work order (d18b1119), timeline event (587f467c)
- 7 parts + 6 labor ops seeded with comp tracking, 9 tech assignments (Skylar/Ernie/CJ)
- `work-order-lifecycle` edge function: 11 actions covering full boss→client→tech flow
- DB migrations: `technician_work_order_lifecycle`, `purchase_orders_auto_ordering`, `work_order_timeline_sync`
- Auto-ordering: 2 POs auto-created (Summit Racing $493.97, etrailer $281.04) with buy URLs
- 5 supplier accounts seeded (Summit, AutoZone, RockAuto, etrailer, RealTruck)
- `sync_work_order_to_timeline()` DB function — every state change auto-refreshes timeline metadata
- Timeline event metadata enriched with live summary (parts/labor/POs/techs/payment status)
- Linked parts/labor to `timeline_event_id` so existing components (WorkOrderViewer, ComprehensiveReceipt) find the data
- Frontend: added `service` + `work_completed` to VehicleTimeline EventType union + color map
- Data flows through all existing surfaces without new UI — timeline event → parts/labor → receipt views

### [VP AI] Tier-2 ONNX models uploaded to Modal + sidecar redeployed — 2026-02-27
- Training complete: german (65.8%), british (58.9%), japanese, italian, french, swedish
- Uploaded hier_<family>.onnx + hier_labels.json to Modal volume yono-data
- Redeployed Modal sidecar (yono-serve-fastapi-app) — tier-2 hierarchical inference live
- Task fdf5038f COMPLETED


**Append-only. Add entries when completing significant work.**
Agents read this to avoid rebuilding things that already exist.

## 2026-02-28

### [sdk] @nuke1/sdk v1.5.0 — Vision namespace aligned with live API
- Rewrote `VisionAnalyzeResult` type to match actual `api-v1-vision` v1.1 output (was using pre-deployment spec)
- Added `nuke.vision.health()` method and `VisionHealthResult` type
- Added `VisionBatchItemResult` type, `VisionAnalyzeParams.include_comps` option
- Added `yono_source` field to `VisionClassifyResult`
- Smart auth: `nk_live_*`/`nk_test_*` keys use X-API-Key, JWTs/service keys use Bearer
- Vision timeouts: analyze 90s, batch 120s (accounts for Modal cold start)
- All 4 methods verified end-to-end against live API: classify (370ms), analyze (4.8s), batch, health
- File: `tools/nuke-sdk/src/resources/vision.ts`

### [automation] launchd Plists for FB Marketplace Sweep + Mail.app Intake
- Created `~/Library/LaunchAgents/com.nuke.fb-sweep.plist` -- daily 6:00 AM sweep: `dotenvx run -- node scripts/fb-marketplace-local-scraper.mjs --all --max-pages 50`, logs to `/tmp/fb-sweep-daily.log`
- Created `~/Library/LaunchAgents/com.nuke.mail-intake.plist` -- persistent daemon with KeepAlive: `dotenvx run -- node scripts/mail-app-intake.mjs --daemon`, logs to `/tmp/mail-intake.log`
- Killed old nohup mail-intake process (PID 94718), replaced with launchd-managed daemon (PID 96910)
- Both loaded via `launchctl load` and confirmed via `launchctl list | grep nuke`
- NOTE: Mail intake hits "authorization denied" on Mail.app SQLite DB -- /bin/bash needs Full Disk Access in System Settings > Privacy & Security

## 2026-02-27

### [agent-architecture] Agent Hierarchy — Haiku/Sonnet/Opus Tiered Extraction System
- Built and deployed three new edge functions:
  - `haiku-extraction-worker` — Haiku-powered extraction worker ($1/$5 MTok). Handles routine extraction, title parsing, field extraction from HTML/markdown. Processes import_queue items. Auto-approves quality >= 0.9, escalates low-confidence to supervisor.
  - `sonnet-supervisor` — Sonnet-powered supervisor ($3/$15 MTok). Reviews Haiku escalations, corrects errors, handles edge cases (replicas, restomods), generates quality reports. Dispatches Haiku work and reviews results in single loop.
  - `agent-tier-router` — Top-level router. Classifies tasks by complexity, routes to right tier. Includes Opus strategy layer for source prioritization and market intelligence. Pipeline runner for continuous processing cycles.
- Shared module `_shared/agentTiers.ts` — Tier configs, Anthropic API wrapper, JSON parsing, quality assessment, cost estimation, task classification
- Updated import_queue CHECK constraint to include `pending_review` and `pending_strategy` statuses
- Tested with real data: 18 items processed, Haiku title parsing (5 titles in single API call), Sonnet caught Ferrari Testarossa replica edge case and escalated
- Sonnet corrected: Dodge "Superbee" → "Super Bee", caught URL/title data conflicts, reduced over-confident title-only scores
- Cost: $0.0017 for 18 operations (essentially free). 67-99% savings vs Sonnet-only.
- Updated TOOLS.md with full agent hierarchy section including tier routing rules and import_queue status flow

## 2026-02-27

### [yono] YONO Sidecar Complete — Tier-2 Models + Consumer Vision API
- **Tier-2 ONNX export**: Built `yono/scripts/export_tier2_onnx.py` to export tier-2 family-specific models from PyTorch to ONNX. Exported 6 families: american (20 classes), german (5), british (15), japanese (8), italian (6), french (2).
- **Modal volume upload**: Uploaded all tier-2 `.onnx` + `.onnx.data` files + updated `hier_labels.json` to Modal volume `yono-data`. Fixed issue where `.onnx.data` weight files were missing (ONNX external data format).
- **Modal sidecar redeployed**: `modal_serve.py` now loads all 6 tier-2 families. Health endpoint confirms: `tier2_families: [american, british, french, german, italian, japanese]`.
- **Classify now returns actual makes**: Before: `"make": "german"` (family only). Now: `"make": "Mercedes-Benz"`, `"family": "german"`, with full top-5 within family.
- **`api-v1-vision` rewritten** (v1.1): The consumer API now calls both YONO `/classify` (make detection) and `/analyze` (condition/zone/damage) in parallel. Returns unified result with make, family, condition_score, vehicle_zone, damage_flags, modification_flags, photo_quality, interior_quality, photo_type, comps. Auth token now sent to sidecar. Optional `include_comps` parameter fetches comparable sales.
- **End-to-end verified**: `POST /api-v1-vision/analyze` returns full vehicle intelligence from a single photo URL at $0.00/image. All 5 edge functions tested: `yono-classify`, `yono-analyze`, `yono-batch-process`, `yono-vision-worker`, `api-v1-vision`.
- Edge functions: `yono-classify`, `yono-analyze`, `yono-batch-process`, `yono-vision-worker`, `yono-keepalive`, `api-v1-vision` all deployed and working.

### [platform] Verify + extend vehicle profile P0 fix (tasks bda3c25b, 6d9cbe9f)
- Confirmed fix from commit 5ee11e181 works: DB migration removed vehicle_price_signal(), price_history, documents subqueries; LIMIT 200 images; frontend RPC timeout 8s→2.5s
- All test vehicles return HTTP 200 in <500ms via anon REST key
- Found residual risk: 1,597 vehicles with 500+ images still borderline (2.3s cold cache, <3s limit)
- Applied v2 fix (migration 20260227235000): LIMIT 200→50, redundant ORDER BY removed, stats.image_count simplified to index-only COUNT(*)
- Root cause of outliers: data quality — vehicles with 10K+ identical duplicate URLs (VW Vanagon 10742, Olds Vista Cruiser 9529). Separate task filed (P65).
- Commits: 5ee11e181 (original), 3ec4a7b34 (v2 hardening)

### [platform] Fix search_vehicles_fuzzy autocomplete timeout (task df34b79a)
- Root cause: `SET statement_timeout TO '3s'` hardcoded in function config; 1.2M vehicle table full-scans at 96s exceeded it → HTTP 500 on autocomplete
- Removed `statement_timeout` from function `proconfig` (was `{search_path=public,statement_timeout=3s}`, now `{search_path=public}`)
- Added `idx_vehicles_make_model_trgm`: GIN trigram index on `(lower(make) || ' ' || lower(model))` with partial filter `is_public=true AND year/make/model NOT NULL` (80MB, valid)
- Updated function WHERE clause to use `(lower(v.make) || ' ' || lower(v.model)) % query_text` — exact index expression match required for Bitmap Index Scan
- Query plan changed from 96s Parallel Index Scan (seq filter) → Bitmap Index Scan on idx_vehicles_make_model_trgm
- Migration: `supabase/migrations/20260227240000_fix_search_vehicles_fuzzy_timeout.sql`

### [platform] Fix api-v1-market-trends 500 timeout (task ffaeabaf)
- Root cause: COALESCE(el.sold_at, v.created_at) prevented date filter pushdown → full 69K Porsche scan; CTE fence blocked per-bucket index range scans
- Added `idx_external_listings_sold_vehicle_at` (vehicle_id, sold_at) WHERE listing_status='sold'
- Added `idx_vehicles_make_sale_date` (lower(make), sale_date) WHERE sale_date IS NOT NULL AND sale_price > 0
- Ran ANALYZE vehicles (was estimating 1,140 rows vs actual 13,029)
- Rewrote `get_market_trends()`: RETURN QUERY EXECUTE USING + generate_series as outer loop → per-bucket index range scans + uses vehicles.sale_date (real auction date)
- Result: 320ms warm / 2.9s cold HTTP 200 (was HTTP 500 at 15s+)
- Migration: 20260227250000_fix_market_trends_timeout.sql

### [platform] P80 Cron audit + deactivation — 116 → 98 active jobs (task 8bd329c7)

Audited all 116 active cron jobs against 4 criteria: no-op/broken commands, broken auth (current_setting/vault), redundant health checks, duplicate extraction workers.

Deactivated 13 jobs:
- `auto-extract` (job 24): pure no-op (`SELECT 1`)
- `concierge-villa-discovery` (job 90): broken auth pattern (app_config table lookup)
- `mecum-extraction-cron` (job 71): only inserted a run record, no actual extraction
- `cron-startup-timeout-alert` (job 328): low-priority monitoring noise
- `agent-monitor-scan` (job 235): redundant with extraction-watchdog (117)
- `extraction-health-check` (job 110): redundant with extraction-watchdog (117)
- `observation-migration` (job 82): broken COALESCE/current_setting auth; run on-demand
- `enrich-bulk-continuous` (job 170): duplicates more-frequent enrich-bulk-mine/derive/vin jobs
- `aggressive-backlog-clear` (job 65): redundant with bat-extraction-worker-1/2/3 and continuous-queue-processors
- `live-auction-sync` (job 87): vault auth broken; sync-live-auctions (109) covers every 15min
- `source-health-monitor` (job 21): low-value health check via old trigger_agent_execution dispatch
- `auto-sort-telegram-photos` (job 128): low-priority, deferrable
- `analyze-unprocessed-org-images` (job 60): low-priority, deferrable

Final: **98 active jobs** (target ≤120) | **13 per-minute jobs** (target ≤20)

### [platform] P95 Cron schedule stagger — eliminate startup timeout bursts (task 2bc2764c)

Root cause confirmed: all 5 valuation-backfill-workers were at `1-59/2 * * * *` (all odd minutes),
running ~120s each and holding 5 slots into the next odd-minute tick. At minute 16:53 this caused
13 startup timeouts for bat-queue-worker-2, bj-queue-worker-2, yono-vision-worker-2, enrich jobs, etc.

Fix: moved valuation-backfill-worker-1 (job 322) and valuation-backfill-worker-3 (job 324) from
`1-59/2` to `*/2` (even minutes). Split cluster: 3 workers at odd, 2 at even.

Also confirmed prior cron cleanup (16:30 UTC) already reduced `* * * * *` from 44 → 13 (all
critical extraction queue workers, correctly below the 20-job target).

Result: 0 startup timeouts across 6 consecutive minutes post-fix. Max concurrent starters per
minute: ~21 (well under cron.max_running_jobs=32).

### [frontend] P92 Full frontend page audit + 2 infinite loading fixes — commit 74432d368

Audited ~70 pages in nuke_frontend/src/pages/ (plus module routes, admin/ pages).

**What was checked:**
- All demo-flow pages: MarketExchange, MarketFundDetail, MarketDashboard, MarketSegments, MarketSegmentDetail, Portfolio, PortfolioWithdraw, BrowseInvestments, InvestorDashboard, OrganizationProfile, Organizations, Dashboard, VehiclesDashboard, AcquisitionPipeline, InvestorOffering
- Auth pages: Login, OAuthCallback, ResetPassword
- Settings: ApiKeysPage (clean), WebhooksPage (weak auth), UsageDashboardPage (clean)
- Admin module (protected by AdminShell): All pages clean
- All other pages: Profile, MyAuctions, SocialWorkspace, VaultPage, ShopFinancials, PersonalPhotoLibrary, MarketIntelligence, CollectionsMap, InvestorDealPortal, VehiclePortfolio, DeveloperSignup, SubscriptionSuccess, TransferPartyPage, StripeConnectStore, ContractStation, MarketMovement, TeamInbox, Notifications, BaTMembers, Library, Capsule, Capture, CurationQueue, UnlinkedReceipts, ImportDataPage

**TypeScript check: CLEAN (npx tsc --noEmit passes)**

**Bugs found and fixed (this commit):**
1. EditVehicle.tsx — infinite loading spinner for unauthenticated users (loadVehicle() only called when user non-null; loading=true never resolved). Fixed: redirect to login + setLoading(false) after fetchUser() returns null.
2. MarketDetail.tsx — infinite "Loading..." when market ID not found (.single() returns null; `if (!market)` showed Loading forever). Fixed: add marketLoading state, proper "Market not found" UI with back link.

**Previously fixed (commit 4e43f29f3):**
- AdminMissionControl.tsx: missing vehicleImageQueue state declaration
- ExtractionMonitor.tsx: broken import AnalysisModelPopup + type error
- ImageProcessingDashboard.tsx: interval scope bug
- Dashboard.tsx: optional notes param type
- Library.tsx: doc→book variable name
- AdminAnalytics.tsx: boolean|null type narrowing
- BidMarketDashboard.tsx: useRef initialization

**Remaining minor issues (sub-tasks filed):**
- vp-platform P72: Add auth guards to BusinessSettings, WiringPlan, WebhooksPage, StripeConnect (non-demo pages, show blank for unauth)
- vp-platform P68: Fix investor-portal-stats timeout (InvestorOffering shows empty stats section)

## 2026-02-27

### [vp-platform] PGRST002 startup-timeout spike alert (task 499b1e16)
- Deployed edge function: `cron-startup-timeout-alert` — queries cron.job_run_details for startup timeout spikes
- Created RPC: `count_startup_timeouts_last_2min()` (SECURITY DEFINER, cron schema access)
- pg_cron job 328: every 5 min, fires Telegram alert if >10 startup timeouts in last 2 min
- Would have detected the 2026-02-27 07:41 PGRST002 outage within 2 minutes
- Migration: supabase/migrations/20260227235900_cron_startup_timeout_alert.sql

### [vp-platform] Header wordmark — add NUKE brandmark to top-left (task 723ab790)
- Added permanent `Link to="/"` with text "NUKE" before `NukeMenu` in `AppHeader.tsx`
- Changed `NukeMenu` trigger button from "Nuke ▶" to hamburger icon "≡" (avoids double branding)
- Added `.nuke-wordmark` CSS class in `header-fix.css`: bold, letter-spaced, hover-dim

### [vp-platform] Fix api-v1-comps 401 for anon users (task c8537818)
- Removed auth requirement from api-v1-comps — comps are public auction results, no auth needed
- Changed authenticateRequest() to be non-blocking (still runs to identify caller but doesn't gate)
- Vehicle profile comparable sales section now works for all anonymous visitors
- Validated: curl with anon key returns 200 + 20 Porsche 911 comps

### [vp-platform] BidMarketDashboard Recharts type fixes (task 78e57dde)
- Fixed `labelFormatter` type: removed explicit `(v: string)` annotation (Recharts expects `string | number`)
- Fixed `formatter` type: removed explicit `(value: number, name: string)` annotations, added `String()`/`Number()` coercions inside (Recharts `ValueType` is `string | number | (string|number)[]`)
- `useRef` lines (78, 226) were already correct with `| undefined` union and `undefined` initial value

### [vp-platform] ralph-spawn: Per-agent token budget + session budget controls (task 1cceee2e)
- Verified ralph-spawn.mjs already has full implementation per CTO/CFO work order
- MODEL_MAP: worker/vp-extraction/vp-orgs/vp-docs/vp-photos → haiku; vp-ai/vp-platform/vp-vehicle-intel/vp-deal-flow → sonnet; cto/coo/cfo/cpo/cdo/cwfto → opus
- TOKEN_DEFAULTS: haiku=30k, sonnet=60k, opus=100k (overrideable via --max-tokens-per-agent)
- --session-budget N: stops pulling tasks when cumulative tokens >= N (0 = unlimited)
- OPUS_CONCURRENCY_CAP=3: hardcoded guardrail, polls every 5s for a slot
- Token usage (tokens_used, input_tokens, output_tokens) logged to agent_tasks.result on every completion
- --model CLI flag still overrides all per-agent routing (backward-compatible)

### [vp-platform] cron.max_running_jobs=20 — BLOCKED (Supabase constraint)
- Task 92d64379: attempted ALTER SYSTEM SET cron.max_running_jobs = 20
- Blocked: parameter is PGC_POSTMASTER level, requires server restart — not possible on Supabase managed Postgres
- ALTER SYSTEM, ALTER DATABASE, and set_config() all fail with permission denied or "requires restart" error
- Current value remains 32. Mitigation already in place: cron cleanup reduced top-of-hour peak from 48+ → 30 jobs
- If formal cap enforcement needed: file Supabase support ticket to modify postgresql.conf directly

### [vp-platform] Quality backfill cron jobs deactivated — backfill 100% complete
- All 1,256,073 vehicles now have data_quality_score populated
- Job 237 (quality-backfill-worker-1): deactivated via cron.alter_job()
- Jobs 238-240: already removed in prior cleanup session
- No indexes to recreate (idx_vehicles_quality_score + idx_vehicles_quality_backfill were dropped; can recreate now if needed)

### [vp-extraction] pg_cron job startup timeout cascade — diagnosed and fixed
- Root cause: `cron.max_running_jobs=32` hard limit being exceeded at peak minutes
- **Fix 1**: `quality-backfill-worker-1` held slots 18-124s every minute → changed `* * * * *` → `2-59/5 * * * *` (prevents slot stacking, worst-case 124s < 300s interval)
- **Fix 2**: `bat-snapshot-parser-continuous-2` had `pg_sleep(30)` hack holding slot → removed sleep, offset to `1-59/3` (fires :01,:04,:07... separate from job 173)
- **Fix 3**: `bat-snapshot-parser-continuous` moved to `2-59/3` (fires :02,:05,:08... avoids :00 peak)
- **Fix 4**: Deactivated `refresh-bid-analytics-mvs` (failing every run — MVs don't exist)
- **Fix 5**: Staggered 18 `*/5` jobs into 5 offset groups (3 at :00, 5 at :01, 5 at :02, 4 at :03, 4 at :04)
- **Fix 6**: Split 13 `*/2` jobs into even (6) and odd (9) groups to halve burst at even minutes
- **Fix 7**: Staggered hourly (5 of 8 moved to :02, :04, :06, :08), `*/10` (3 moved to :03, :06 offsets), `*/15` (2 moved to :02, :04 offsets), `*/30` (3 moved to :02, :07 offsets)
- Result: top-of-hour peak = 30 jobs (was 48+), safely under the 32 limit
- Filed P72 follow-up for `data-quality-workforce` null URL bug

### [vp-vehicle-intel] Signal score coverage diagnosis + api-v1-signal on-demand valuation fix
- Diagnosed: 637K active vehicles with YMM missing nuke_estimate — backfill lag, not data gaps
- Root cause breakdown: 151K vehicles have zero price anchor (no sale/asking/current_value); 486K have comp data but backfill hasn't run yet
- clean_vehicle_prices: 1M rows, 6,144 makes, covers all major collector car makes — comp data is NOT the bottleneck
- Backfill cron: 5 workers (jobs 321-325, every 2min, 100 vehicles each = 15K/hr) deployed by feb786e7 agent — ~42h to full coverage
- Fixed api-v1-signal: now triggers on-demand valuation inline when no estimate exists, instead of returning 404. Adds ~1-3s on first request but returns actual data. `computed_on_demand: true` flag in response. Deployed to production.
- Task f93ef450 completed.

### [backend-triage] Full backend error triage — all public pages and API endpoints
- Ran complete backend error triage against P92 task (founder complaint: pages not loading)
- Tested: api-v1-vehicles, api-v1-exchange, api-v1-comps, api-v1-search, api-v1-signal, api-v1-market-trends, universal-search, transfer-status-api, inbound-email, investor-portal-stats, get_vehicle_profile_data RPC
- All 18 frontend routes checked — all files exist, no missing imports
- HTTP status check: all Vercel pages return 200 (SPA serving correctly)
- Findings filed as 6 agent_tasks:
  - P78 c8537818: api-v1-comps blocks anon users → vehicle profile shows no comparable sales
  - P75 df34b79a: search_vehicles_fuzzy 3s statement_timeout → autocomplete fails under load
  - P73 ffaeabaf: api-v1-market-trends times out → get_market_trends RPC slow on large makes
  - P72 322eb3ae: investor-portal-stats times out (>15s) → /offering page shows no live stats
  - P65 14add70f: search_vehicles_fts intermittent 503 PGRST002 schema cache errors
  - P60 f1dec0c5: /api/landing transient 404 (verified resolves on retry)
  - P55 a9674637: /predictions shows empty (no open markets, page loads gracefully)
- Healthy: api-v1-exchange, api-v1-signal, transfer-status-api, inbound-email, universal-search (POST), get_vehicle_profile_data, db-stats, api-v1-comps (authenticated)

### [cto] Post-mortem: PGRST002 schema cache outage 2026-02-27 ~07:41–07:47 UTC
- Task b11baf19: full post-mortem written at docs/post-mortems/2026-02-27-pgrst002-schema-cache-outage.md
- Root cause confirmed: 44 `* * * * *` cron jobs converging + long-running quality backfill workers held all 32 max_running_jobs slots; PostgREST schema reload failed at 07:46 → PGRST002 to all callers
- Forensic: cron.job_run_details shows 37 startup_timeouts at 07:41, total blackout (0 succeeded) at 07:46
- Filed 4 work orders to vp-platform: P95 stagger cron schedules, P90 set max_running_jobs=20, P80 deactivate low-priority crons, P75 Telegram alert

### [vp-extraction] Gooding & Company field backfill — engine/transmission/mileage — 2026-02-27
- Task 87446ee0: fill engine/transmission/mileage gaps on 369 Gooding vehicles
- Key insight: Gooding is Gatsby/Contentful — all data in `/page-data/lot/{slug}/page-data.json` (no HTML scraping needed)
- `item.specifications` array has engine/transmission as bullet points; mileage in highlights prose
- Built + deployed: `backfill-gooding-descriptions` edge function — parses engine (spec line containing Engine/Cylinder/BHP), transmission (Transmission/Gearbox/Transaxle), mileage (highlights prose)
- Updated `extract-gooding` extractor to extract these 3 fields for all future runs
- Results: engine 10.3%→35.2% (+244%), transmission 0.3%→25.5% (+8400%), mileage 0.8%→1.1%
- Remaining 65% no engine: pre-war brass-era vehicles (1900-1920s) with empty specs in Contentful — no additional data available
- Cron 319: `*/30 * * * *`, batch_size=20

### [vp-extraction] Description backfill — Mecum + Craigslist — 2026-02-27
- Task ec362475: 945K vehicles missing descriptions — targeted Mecum (~2.2K remaining) + CL (~2.5K)
- Discovery: Mecum already at 95.6% desc coverage (extraction sprint fixed the "8%" stat from task filing)
- `backfill-mecum-descriptions`: archive-based, zero-cost — queries listing_page_snapshots WHERE platform='mecum', re-parses __NEXT_DATA__ blocks (HIGHLIGHTS + EQUIPMENT) without any live fetch. Also fills mileage + engine_size + transmission.
- `backfill-cl-descriptions`: live-fetch via archiveFetch — CL pages expire fast, historical ~100% expired (410). Will catch newly-added CL vehicles while pages are still live.
- Cron 317 (`*/10 * * * *`): backfill-mecum-descriptions, batch_size=25 — draining ~2.2K remaining at ~15/run
- Cron 318 (`*/30 * * * *`): backfill-cl-descriptions, batch_size=15
- VIN intentionally excluded from Mecum backfill (handled by backfill-vin-from-snapshots, avoids unique constraint conflicts)
- Note: NULL discovery_source vehicles (~820K missing desc) are BaT/conceptcarz — different scope

### [vp-extraction] RM Sotheby's lot page scraper + description backfill — 2026-02-27
- Task 9fb1563a: RM Sotheby's vehicles missing description/mileage/engine (API only returns list-page data)
- Built + deployed: `backfill-rmsothebys-descriptions` edge function (557 lines)
  - Fetches individual lot detail pages via archiveFetch (Firecrawl, cache-first)
  - Parses: description (3 HTML pattern strategies), bullet highlights, chassis/engine IDs, estimate range, mileage from text
  - Writes: description, mileage, origin_metadata (estimate_low/high, chassis_number, engine_number, location)
- Fixed: VIN unique constraint violations — chassis numbers now stored in origin_metadata only
- Cron 268 (`rmsothebys-description-backfill`): every 30min, batch_size=20
- Progress: 1.3% → 12.2% description coverage (153/1,251), continuing to drain

### [vp-platform] Homepage Browse Feed P0 fix — 2026-02-27
- Task 0139bb65: "Unable to load vehicles" error when clicking Browse Feed
- Root cause: getMissingColumn() regex only matched Postgres 42703 "column X does not exist" format. PostgREST PGRST204 schema-cache errors use different format: "Could not find the 'X' column of 'vehicles' in the schema cache" — unmatched → getMissingColumn returned null → selectV1 fallback never ran → fell through to setError
- Fix 1: Extended getMissingColumn to also parse PGRST204 message format
- Fix 2: Removed `if (missingColumn)` guard — ANY selectV2 error now always falls back to selectV1
- Commit 4ac104ca6, pushed to main

### [vp-extraction] Queue backlog triage — 2026-02-27 16:15 UTC
- Task 23f1da15: Import queue at 41K pending (demand spike, not stall)
- Root cause: Mecum Live Auctions (25K items) had only 2/5 workers active; C&B (15K) had 6 workers
- Fix: Re-enabled mecum-live-queue-workers 3-5 (cron jobs 253-255) → all 5 now active
- Throughput confirmed at ~5,100/hr; estimated full drain ~5-6 hours
- 47 failed items (parse/field errors, non-blocking); 404 processing all fresh (<10min)

### [vp-platform] Search loading skeleton — 2026-02-27
- Task b9e49520: SearchResults.tsx had minimal skeleton (6 simple boxes + "Searching..." text)
- Replaced with proper shimmer skeleton: fake summary bar + 8 card-shaped placeholders matching grid (260px minmax, 160px image, 3 text stubs)
- Early return at line 208 blocks NO RESULTS empty state when loading=true
- Loading prop wired: Search.tsx:1084 → SearchResults loading prop

### [vp-extraction] Import Queue Backlog Cleared — 2026-02-27
- Investigated 41K pending (not stalled — 384 processing at 5-7K/hr; bulk discovery spike added 93K items 2026-02-26 16-17 UTC)
- Fixed: 544 exhausted items (attempts >= 3) stuck in `pending` — marked `failed`
- Fixed: 47 genuinely failed items for working domains reset to `pending` (attempts=0)
- Activated: 4 inactive Mecum workers (jobs 242-245) — 10 total Mecum workers now
- Activated: 3 inactive Mecum Live workers (jobs 253-255) — 5 total Mecum Live workers now
- Queue post-fix: 41K pending, 13 failed, ~333 processing

### [vp-ai] YONO Sidecar Unreachable — FIXED 2026-02-27 16:10 UTC
- Root cause 1: Supabase secret `YONO_SIDECAR_URL` had typo `sss73133` instead of `sss97133`
- Root cause 2: `yono-classify` timeouts too short (health 15s, classify 10s) vs Modal latency 30-40s
- Fix: Corrected Supabase secret, increased yono-classify timeouts to 45s/60s, redeployed Modal sidecar
- Verified: `available:true` end-to-end; image classification no longer falling back to cloud AI

### [cwfto] Situational Brief + Cleanup — 2026-02-27 ~16:10 UTC
- Quality backfill: 100% COMPLETE — all 1,256,073 vehicles have data_quality_score. Filed P92 task to deactivate cron jobs 237-240.
- YONO training: british tier-2 active (PID 37505). YONO sidecar still unreachable — filed P90 task (redeploy after ONNX export).
- Import queue: 41K pending (Mecum 25K, C&B 15K). All queues draining normally.
- Stale task cleanup: Reset 7 in_progress tasks to pending, completed 4 confirmed-done tasks, closed 2 duplicates.
- Filed: 3 follow-up tasks (quality backfill deactivation, YONO sidecar, vehicle profile P0 verify).
- Twilio: Still unblocked — CFO/founder action still required (P92/P88 tasks live).
- Next CWFTO loop scheduled (P92 pending).

## 2026-02-27

### [platform] ralph-spawn: per-agent token budget + session budget controls — task 1cceee2e
- Added MODEL_MAP: worker/vp-extraction/vp-orgs/vp-docs/vp-photos→haiku, vp-ai/vp-platform/vp-vehicle-intel/vp-deal-flow→sonnet, cto/coo/cfo/cpo/cdo/cwfto→opus
- Added --max-tokens-per-agent N flag (defaults: haiku=30K, sonnet=60K, opus=100K)
- Added --session-budget N flag: stops pulling tasks when total token spend hits cap
- Added Opus concurrency cap: max 3 Opus agents simultaneously (hardcoded cost guardrail)
- Token usage (tokens_used, input_tokens, output_tokens) now logged to agent_tasks.result on every completion
- --model flag still overrides per-agent routing (backward compatible)
- File: scripts/ralph-spawn.mjs

### [frontend] Search filter panel fix — task c774b1cd
- `showFilters` defaulted to `true` in DEFAULT_FILTERS — filter inputs now expand automatically when vehicle results appear
- Added `make` field to VehicleFilters interface, DEFAULT_FILTERS, filter logic (substring match), and UI input
- Filter panel now shows: Make, Price (min/max), Year (min/max), Max Mileage, Transmission, Status
- File: `nuke_frontend/src/pages/Search.tsx` lines 21-41, 578-600, 912-930

### [coo] CFO memo surfaced — image pipeline unpause (task 1131e863)
- Delivered CFO memo to CEO: $3,250 max backfill cost, $150/month ongoing, 65-day clearance
- YONO-first hybrid model: 60% free via YONO, 40% Gemini Flash at $0.0001/image
- $50/day hard cap already coded in analyze-image — zero runaway risk
- Decision awaiting CEO: remove NUKE_ANALYSIS_PAUSED from Supabase secrets
- Unlocks: camera geometry, subject taxonomy, NL descriptions, VIN tag detection

### [frontend] Investor offering gate stats — task ac67d3b6
- Updated `gateStats` in InvestorOffering.tsx access-code screen with confirmed live numbers
- Was: 18K vehicles, 33M images, 200K auction events, <$100M AUM gap
- Now: 1.25M vehicles, 33.7M images, 513K AI valuations, 4 market segment ETFs
- Updated headline subtitle text to match new numbers
- File: `nuke_frontend/src/pages/InvestorOffering.tsx` lines 575–580, 634

### [frontend] Search performance + skeleton UX — task 6db748af
- Switched IntelligentSearch.tsx edge function call from slow `search` (11s) → `universal-search` (3.8s)
- Mapped universal-search result types to frontend types: vin_match→vehicle, tag→reference, external_identity→user
- Upgraded skeleton loading in SearchResults.tsx: 8 realistic card skeletons (image + text lines) instead of 6 plain blocks
- Files: nuke_frontend/src/components/search/IntelligentSearch.tsx:681, nuke_frontend/src/components/search/SearchResults.tsx:208

### [extraction] FB Marketplace GraphQL probe — task 62f30b2e
- Logged-out GraphQL CONFIRMED working from residential IPs. doc_id: 33269364996041474
- Returns 24 listings/page: id, title, price, city/state, thumbnail, is_sold/pending flags
- BLOCKED from Supabase datacenter IPs (error 1675004, IP-level block — not bypassable with tokens)
- Year filter in variables is ignored; must filter by title parsing at upsert time
- Vintage fraction: ~8-17% per metro (title-parsed)
- Infrastructure: fb-marketplace-local-scraper.mjs (43 metros), fb-relay-server.ts (port 8787)
- 3 paths forward documented in facebook-marketplace-extraction.md (residential scraper / relay integration / session replay)
- Relay path requires /graphql-sweep endpoint on fb-relay-server.ts (not yet built)

### [frontend] Search empty state: featured vehicles grid — task a2e04f6a
- /search with no query now shows 24 top vehicles by sale_price in a VehicleCardDense grid
- Added "Top Vehicles by Value" label; quick-search chips preserved above grid
- useEffect fetches public vehicles with primary_image_url, ordered by sale_price DESC
- Commit e42d60803

### [platform] Vehicle intelligence cron jobs applied — task 6fe1a113
- Job 314: compute-vehicle-valuation-backfill — */10 * * * * — batch_size=50
- Job 315: batch-vin-decode-backfill — */30 * * * * — batch_size=50
- Job 316: batch-ymm-propagate-hourly — 0 */4 * * * — batch_size=500
- Migration 20260227140000_vehicle_intel_crons.sql applied via SQL MCP (migration push was blocked by legacy ordering)

### [frontend] Add Search + Market to header nav (task 99850151)
- Added Search and Market as visible `<Link>` elements in `header-left` beside NukeMenu button
- Changed `header-slot-left` grid column from `8%` to `max-content` so left slot sizes to content
- Added `.header-main-nav { display: none }` under `@media (max-width: 600px)` — hidden on mobile
- Files: `nuke_frontend/src/components/layout/AppHeader.tsx`, `nuke_frontend/src/styles/header-fix.css`

### [security] Key Guardian daily audit — task 0e8b5ca1
- gitleaks: 0 findings in last 50 git commits and working tree (clean)
- Known-bad keys: Gemini API key + Stripe webhook secret still present in .env (ACTION REQUIRED — unrotated)
- Email report sent to founder via Resend (ID: 67a62aef-5124-4797-a1af-98aeb5409ce0)
- Task marked completed in agent_tasks DB

### [frontend] Fix P0: /market routes to MarketExchange (live ETF data)
- Changed root `/` and `/dashboard` routes in marketplace/routes.tsx from MarketDashboard (Coming Soon stub) to MarketExchange
- nuke.ag/market now shows live PORS/TRUK/SQBD/Y79 fund cards instead of hardcoded "Coming Soon" page

### [frontend] TeamInbox avatars + inline images + thumbnails — commit fe7785858
- 36px sender initials avatar circle added to every email list row (left of text content)
- Detail pane header avatar bumped to 48px
- Refactored SenderAvatar to use shared `getAvatarColor` (deterministic HSL hash) + single-char `getInitials`
- Added `CarIcon` SVG component prepended to vehicle URLs in Alerts tab
- Scoped `.email-body` CSS: img responsive, links colored, blockquote indented, table borders
- `dangerouslySetInnerHTML` div gets `className="email-body"` for proper HTML email rendering
- Image attachment thumbnails grid (80x80, object-cover) for attachments with `content_type: image/*` + `url`

### [frontend] TeamInbox Gmail-style 3-pane redesign — commit 9c0553683
- Rebuilt visual layer of TeamInbox.tsx (815 insertions, 501 deletions)
- Layout: 220px fixed sidebar + 360px scrollable middle list + flex-1 detail pane
- Left sidebar: INBOX header, icon+label+badge tabs (Emails/Messages/Alerts), mailbox color-dot list
- Middle pane: 64px email rows, 3px left accent bar (mailbox color for unread, primary for selected), sender bold/normal, subject, snippet truncated
- Detail pane: initials avatar circle (deterministic hue from email hash), sender name 16px bold, meta strip with mailbox badge pill + timestamp, HTML body renderer, Archive/Spam ghost buttons with hover, reply textarea + Send Reply primary button
- All colors use design system tokens (var(--bg), var(--surface), var(--border), var(--text), var(--accent), var(--text-muted))
- Mobile: scoped CSS media query hides sidebar + right pane, shows bottom tab bar at <768px
- All logic preserved: useEffect, useState, supabase queries, realtime subscriptions, compose modal

### [security] Key Guardian — automated secret scanning + daily audits — commit cf0b94722
- gitleaks v8.30.0 installed locally (brew)
- .gitleaks.toml: catches Stripe (sk_/rk_/whsec_), Google/Gemini (AIza*), Resend (re_*), Supabase JWT, Twilio (32-char hex, entropy 3.5), Modal (ak-*); allowlists .env.vault, node_modules, placeholders
- .claude/agents/key-guardian/CLAUDE.md: full agent persona — startup ritual, rotation workflow, tool inventory, known-compromised key table
- scripts/key-audit.sh: daily bash audit — gitleaks detect on last 50 commits + working tree, checks .env for known-bad keys, emails founder via agent-email → Resend
- .git/hooks/pre-commit: prepended gitleaks protect --staged before existing TypeScript check — blocks commit with actionable message if secrets found
- DB: key-guardian registered in agent_registry; daily audit task inserted in agent_tasks (id=0e8b5ca1, P95)
- FOUNDER_EMAIL=toymachine91@gmail.com set in Supabase secrets (required for agent-email → real email delivery)
- First audit ran: ACTION REQUIRED — 2 unrotated known-bad keys in .env (Gemini + Stripe webhook)
- Activation email sent to founder (Resend ID: 130dbf6b)
- Pre-commit hook verified working: ran gitleaks on setup commit, passed clean

### [security] Stripe Connect Security Audit + Hardening — commit 8ec743ad9
- Audited all 7 Stripe Connect surfaces: 4 edge functions + 2 frontend pages + 1 migration
- Found and fixed 4 CRITICAL issues:
  - stripe-connect-account: Added JWT auth guard on all actions (was fully unauthenticated)
  - stripe-connect-products: Added JWT auth + ownership check on POST/create
  - stripe-connect-checkout: Fixed application fee bypass — fee now computed from Stripe-authoritative price (not client-supplied priceInCents)
  - stripe-connect-checkout: Added JWT auth guard on subscription + billing_portal actions
- Found and fixed 4 HIGH issues:
  - CORS: All 4 functions restricted from Access-Control-Allow-Origin: * to https://nuke.ag
  - IDOR: Added ownership checks on get_link + status actions in stripe-connect-account
  - Data minimization: stripe-connect-account status no longer returns full Stripe account object
  - RLS: stripe_subscriptions had RLS enabled but zero policies — added SELECT policy via stripe_connect_accounts FK join
- 4 MEDIUM issues documented, pending founder action (STRIPE_WEBHOOK_SECRET verification, slug URLs, API version pin, rate limiting)
- Sent audit report to founder via agent-email (Resend message_id: b1486a50-534d-40ea-baf0-9cd137f942a1)
- All 4 functions deployed to Supabase, committed + pushed to main

### [stripe] Full Stripe Connect Integration — commit 5528063ab
- stripe-connect-account edge function: create V2 connected accounts, onboarding links, live status check
- stripe-connect-products edge function: create products on connected accounts, list with expanded prices
- stripe-connect-checkout edge function: direct charge (5% platform fee), subscription, billing portal
- stripe-webhook updated: V2 thin event parsing (requirements.updated, capability_status_updated), stripe_subscriptions upsert, all previous handlers preserved
- DB: stripe_connect_accounts (user_id FK, RLS), stripe_subscriptions tables (migration 20260227160000)
- Frontend StripeConnect.tsx: create account, onboarding, status dashboard, product management, store link
- Frontend StripeConnectStore.tsx: public storefront, product cards, Buy Now → Stripe Checkout, success state
- Routes: /stripe-connect, /stripe-connect/store/:accountId in DomainRoutes.tsx
- AdminShell nav: "Stripe Connect" added to Tools section
- All 4 functions deployed, frontend build clean (✓ built in 11.86s), pushed to main

## 2026-02-27

## 2026-02-27

### [vehicle-intel] VP Vehicle Intel session audit — deployed missing functions, filed cron tasks
- Deployed batch-ymm-propagate (was NOT deployed): filled 286 factory fields across 63 vehicles in first run
- Deployed batch-vin-decode (was NOT deployed): dry run shows 37/50 candidates are pre-1981 non-standard VINs (NHTSA won't decode)
- Completed agent_task 1489e336 (YMM propagation backfill P60): 63 vehicles updated, 286 fields filled
- Key coverage finding: 513K/1.25M active vehicles have nuke_estimate (40.9%)
- Exchange health: 4 NAVs updating correctly via update-exchange-prices (PORS/SQBD/TRUK/Y79)
- Exchange full cycle confirms: ok, 4 navs updated, 0 offerings (no live trades, expected)
- No crons found for compute-vehicle-valuation, batch-vin-decode, or analyze-market-signals
- Manually ran 8 valuation batches x50 = ~400 new nuke_estimates computed this session
- Filed 3 follow-up tasks:
  - 6fe1a113 (P85, vp-platform): Apply 3 cron jobs via Supabase Dashboard SQL editor
  - f93ef450 (P75): Signal score coverage — 59% missing, root cause is missing valuation cron
  - 0e57d34a (P60): VIN decode gap — pre-1981 non-standard VINs, NHTSA can't decode
- api-v1-exchange error was a false alarm: works with ?action=funds, default action=snapshot also works
- Migration 20260227140000_vehicle_intel_crons.sql: written, NOT yet applied (migration ordering conflict)

### [yono] YONO sidecar URL typo fixed — P85 resolved
- Root cause: YONO_SIDECAR_URL in Supabase Edge Function secrets had typo: sss73133 instead of sss97133
- Fix: `supabase secrets set YONO_SIDECAR_URL=https://sss97133--yono-serve-fastapi-app.modal.run`
- Redeployed yono-vision-worker (v9) and yono-keepalive (v8) to pick up correct URL
- Confirmed: sidecar operational, vision_available=true, uptime sustained
- Vision worker confirmed processing: ~800 images/hr per worker, 2 workers = ~1600/hr effective
- P85 task `db96c02e` marked completed

### [yono] YONO vision worker health audit — vp-photos session
- DB schema cache incident: PostgREST failed ~07:00-08:00 UTC (pool saturation from 10+ agents)
- During outage: cron keepalives failed → sidecar scaled to zero → vision worker offline
- Recovery: DB recovered ~08:00 UTC, sidecar warm at sss97133 URL, all systems nominal
- Filed: CTO post-mortem task (P80), DB scale-down incident documented

### [photos] K10 truck vision analysis status confirmed
- 419 photos (vehicle_id: 6442df03-9cac-43a8-b89e-e4fb4c08ee99): all ai_processing_status=completed
- All 419 have vision_analyzed_at=NULL → eligible for YONO (no ai_processing_status filter)
- YONO claim_yono_vision_batch picks up ANY image with image_url + vision_analyzed_at=NULL
- At 1,600 img/hr: K10 will complete in ~16 min once YONO worker reaches them
- Organization: all 419 unorganized (matching global pattern)

### [photos] Photo organization pipeline gap identified
- 100% of sampled images have organization_status=unorganized (0 organized)
- auto-sort-photos exists but targets telegram/technician workflow, not general inventory
- No cron-scheduled general organization pipeline found
- Filed P72 task for vp-photos to design organization pipeline



### [yono] Scaled YONO vision workers 2→4, Modal sidecar min_containers 1→2
- Added cron workers 3+4 (jobs 286+287): */2 * * * * → same URL/auth pattern as jobs 247+248
- Redeployed Modal sidecar (yono-serve) with min_containers=2 → always 2 warm containers
- New throughput: 4 workers * ~1000 img/hr = 4000 img/hr combined
- K10 (419 photos): ~6 min to complete at new rate (was ~13 min)
- All 32M images: ~333 days (was 667 days at 2 workers)
- To complete in 30 days: need 44 workers — filed as future consideration
### [worker] Import queue cleanup + task triage — worker-session-3
- Closed 8 stale/superseded tasks: 2x BAT queue stall (superseded by process-bat-extraction-queue cron), 2x YONO sidecar unreachable (sidecar verified up), source-census archiveFetch audit (acceptable exception documented), agent type registry
- Reset 243 failed PCarMarket records to pending (extractor fix was deployed by previous session)
- Fixed 44 port-80 BaT URLs (bringatrailer.com:80 → bringatrailer.com); dupes skipped
- Skipped garbage/malformed URLs: N/A suffix dupes, /carfax, %20lol, Google redirect params, BaT browse pages
- Skipped non-vehicle memorabilia: Mecum neon signs/hubcaps/quilts/gas pumps, Gooding literature/programs/sculpture/toys
- Reset transient failures to pending: PGRST002 schema cache (3), Firecrawl 500/502 (2), C&B Invalid JSON (2)
- Remapped 11 legacy agent_tasks (oracle/guardian/sentinel/harvester/curator) to proper VP domains
- Updated REGISTRY.md with active vs legacy agent type table
- Failed queue: 381 → 0 items (100% cleared)

### [extraction] RM Sotheby's description backfill — backfill-rmsothebys-descriptions edge function
- Root cause: SearchLots API returns no description/mileage — only auction metadata
- Built `supabase/functions/backfill-rmsothebys-descriptions/index.ts`
- Fetches individual lot pages via archiveFetch (Firecrawl, cache-first)
- Parsers: description (body-text--copy paragraphs), highlights (list-bullets), ID fields (chassis/engine), estimate ($LOW - $HIGH), mileage (regex in text), VIN (17-char detection from chassis field)
- Deployed, verified: 71/1,251 vehicles backfilled, desc rate 1.3% → 5.7%
- Cron job 268: every 30min, batch_size=10 — will drain remaining ~1,180 in ~2.5 days
- Key discovery: `order=id.asc` avoids statement timeout; `discovery_source='rmsothebys'` is the indexed filter

### [comms] Gmail OAuth alert poller — direct Gmail API polling (backup to Gmail forwarding)
- Built `scripts/gmail-poller.mjs`: local Node.js poller — `--setup` runs OAuth2 consent, `--once`/`--daemon`/`--dry-run` modes
- Built `supabase/functions/gmail-alert-poller/index.ts`: Supabase edge function; polls Gmail API via OAuth2, dispatches to `process-alert-email`
- Migration `20260227130000_gmail_alert_poller_cron.sql`: pg_cron job 265 schedules every 5 min (active)
- Edge function deployed live: returns `{success:false, setup_required:true}` until GOOGLE_REFRESH_TOKEN set
- GOOGLE_CLIENT_ID + GOOGLE_CLIENT_SECRET already set in Supabase secrets
- **ONE STEP remaining**: `dotenvx run -- node scripts/gmail-poller.mjs --setup` → log in as toymachine91@gmail.com → then `supabase secrets set GOOGLE_REFRESH_TOKEN=<token>`
- NOTE: Resend-based approach (alerts@nuke.ag forwarding) is simpler — see entry below. Gmail forwarding is preferred path; OAuth poller is the backup/primary polling option.

### [platform] Resend Inbound Email — Audit, Fix, alerts@nuke.ag wiring
- **Status**: Pipeline was already working. 5 real emails in contact_inbox including shkylar@gmail.com → info@nuke.ag and Amazon SES DMARC reports → privacy@nuke.ag
- **Root finding**: RESEND_API_KEY in Supabase is send-only scope (restricted_api_key) — cannot read domains/webhooks via API. Inbound routing IS configured in Resend dashboard (confirmed by working emails)
- **Bug fixed**: inbound-email was silently losing email body when Resend API content fetch failed. Now uses webhook payload `data.text`/`data.html` as immediate fallback before attempting API enrichment
- **New feature**: Added `alerts@nuke.ag` to VALID_ADDRESSES + routing to process-alert-email → import_queue
  - Email arrives at alerts@nuke.ag → stored in contact_inbox AND forwarded to process-alert-email
  - process-alert-email extracts listing URLs, queues to import_queue with alert_source + ingested_via metadata
  - Supports: BaT, Craigslist, KSL, Hemmings, eBay, Cars.com, AutoTrader, Hagerty, CarGurus, ClassicCars, FB, PCarMarket, C&B
- **Test result verified**: BMW M3 test → alert_email_log: urls_found=1, urls_queued=1, status=processed → import_queue: status=pending, source=bat, ingested_via=email_alert
- **Inserted test record**: contact_inbox email_id=test-001 (from someone@example.com to info@nuke.ag)
- **Deployed**: inbound-email v17 (two fixes: body fallback + alerts routing)
- **DNS/MX**: Already configured — emails ARE flowing. No action needed.
- **What's needed for Gmail→alerts@nuke.ag flow**: Set up Gmail forwarding in toymachine91@gmail.com settings to forward to alerts@nuke.ag

### [frontend] Search + Discovery + Vehicle Cards UX overhaul — committed in 05000c396
- **Loading state**: `loading` initializes `true` when URL has `?q=` param → skeleton shows immediately on page load (not blank)
- **Search summary**: Default changed from stale "Enter a search query..." to empty string → no ghost text after results load
- **Skeleton shimmer**: SearchResults loading state replaced spinner-in-box with animated shimmer card grid (6 cards, `skeleton-shimmer` keyframe)
- **Empty state** (no query): Replaced blank page with popular search suggestion links grid
- **Empty state** (no results): Removed emoji, clean "No results for X" + popular search links
- **VIN Lookup**: Demoted from prominent button to small 7.5pt secondary link, collapsed by default
- **Workstation panel**: Removed from between search/results (was blocking flow), moved to collapsible section at page bottom
- **Search input**: Larger padding (10px), blue focus ring, "Search" button (was "GO") full-height black fill flush right
- **Clear button** (×): Added to search input between text and Search button
- **Type filter pills**: Compact black/white toggle style replaces verbose icon+count+label buttons
- **Controls bar**: Removed redundant Filter type dropdown, simplified to Grid/List + Sort
- **Card hover**: Gallery mode cards get `translateY(-3px)` lift + `box-shadow` on hover
- **Enrichment merge fix**: Used nullish coalescing (`??`) instead of spread (was overwriting valid data with nulls)
- **Edge function** (`supabase/functions/search/index.ts`): `vehicleMetaById` select expanded to include `sale_price, asking_price, mileage, transmission, vin` — metadata now flows through to tier calculation
- **Edge function fix**: Removed non-existent `image_count, event_count` columns from select (were causing silent query failure → no metadata); replaced with `vehicleImageById` presence check
- Deployed: `supabase functions deploy search --no-verify-jwt` ✓
- TypeScript: clean (`npx tsc --noEmit`)
- Search verified: 10 results for "porsche" with sale_price + mileage in metadata

### [vp-orgs] Org cron gap fix — 3 missing crons added, 2 functions deployed
- **classic-seller-queue-worker** (job 264, `*/5 * * * *`): drains `classic_seller_queue`; 109 items were stuck with 5 failed attempts since Dec 2025. Root cause: `index-classic-com-dealer` was not deployed. Fixed: redeployed both functions, reset 109 items to pending, cron draining now (8 completed in first batch).
- **ecr-collection-inventory-refresh** (job 262, `0 3 * * *`): refreshes ECR collection inventory; was 45 days stale. 1,831 collections, 142 never synced.
- **compute-org-seller-stats-daily** (job 263, `0 4 * * *`): rebuilds `organization_seller_stats` for all orgs with external listings. Was 1 entry, stale Feb 14.
- Deployed: `process-classic-seller-queue`, `index-classic-com-dealer`
- Filed agent task for org-to-seller bridge (P70, build when queues populate more data)
- Migration file: `supabase/migrations/20260227100000_vp_orgs_cron_fixes.sql`

### [cdo] Data Quality Audit — 7 work orders filed
- Audited 1.255M vehicles across all sources using pg_stats (fast, no sequential scans)
- **Key findings**: VIN coverage 17% overall, description coverage 25%, signal_score near-zero (0.22%), valuation 41%
- **Source breakdown** (10% sample): User Submission dominates (96% of corpus), Mecum 8% desc coverage, B-J 41% VIN coverage, Craigslist 4% desc coverage
- **BAT extraction stall confirmed**: 119,299 pending items since Dec 2025, stopped processing Feb 5. 142K BaT vehicles effectively have no signal_score as a result.
- **YONO training imbalance confirmed**: 17 of 38 zones have <50 examples. panel_fender_rr/rr=1 example each.
- Filed 7 agent_tasks: vp-extraction (4: VIN backfill P82, Description backfill P80, B-J VIN gap P78, BAT stall P85x2), vp-vehicle-intel (valuation coverage P75), vp-ai (YONO zone balance P72)

## 2026-02-27

### [frontend] TeamInbox — unified team communication hub at /inbox
- Built `/nuke_frontend/src/pages/TeamInbox.tsx` (1294 lines) — full-featured three-tab inbox page
- **Emails tab**: contact_inbox reader, mailbox filters (support/info/privacy/legal/investors/hello), status filters (unread/read/replied/archived), full email detail pane, reply via `reply-email` edge function, archive/spam actions, real-time subscription via Supabase realtime
- **Messages tab**: agent_messages reader, to/from role filters, unread-only toggle, thread view, compose modal (founder→any agent role via `agent-email` edge function), marks as read on open
- **Alerts tab**: filtered view of alert emails (alerts@nuke.ag or subject contains "vehicle alert"), auto-extracts vehicle listing URLs (BaT, C&B, PCarMarket, Mecum, etc.), links for direct access
- Left sidebar: tab nav with live unread count badges, auto-refreshes every 30s
- Auth-gated: redirects to /login?returnUrl=%2Finbox for unauthenticated users
- Uses Nuke design tokens only (var(--bg), var(--text), var(--primary), etc.)
- Route: `/inbox` added to DomainRoutes.tsx
- Nav: "Inbox" link added to NukeMenu (authenticated users) and ProfileBalancePill dropdown
- Committed in 944ba7704, pushed to main (Vercel deploying)

### [worker] Multi-task sprint — 6 tasks completed
- **P90 YONO ACTIVE_AGENTS update (1977ede1)**: Updated ACTIVE_AGENTS.md: zone classifier PID 7241 COMPLETE (epoch 15/15, val_acc=72.8%), tier-2 PID 28401 active training german family, watcher PID 7390 active
- **P85 YONO sidecar unreachable (363eca02)**: Sidecar IS reachable. Task had typo (sss83133 vs sss97133). Verified: health=200, classify_no_token=401, classify_with_token=200. Auth middleware working
- **P80 Import queue backlog (78505a8b)**: Not stalled. 84,847 pending, 353 active, 277K completed. Demand spike from Extraction Quality Sprint draining at ~50/min
- **P75 YONO sidecar Bearer token auth (b6b693ab)**: Already implemented by VP AI. auth_middleware in modal_serve.py lines 374-389, Modal secret nuke-sidecar-secrets and Supabase secret MODAL_SIDECAR_TOKEN both set, yono-classify + yono-analyze both send Bearer token
- **P70 archiveFetch violation: crawl-bat-active (db1d1a69)**: Documented exception — RSS/XML feeds are URL-discovery-only (parse URLs from XML, content not stored). Added comments. Deployed crawl-bat-active
- **P70 archiveFetch violation: sync-live-auctions (7ad92537)**: FIXED — replaced raw fetch("https://bringatrailer.com/auctions/") with archiveFetch() (skipCache: true, platform: bat). Page now archived to listing_page_snapshots. Deployed sync-live-auctions
- **P60 archiveFetch violation: extract-gooding (c8afcd1e)**: Documented exception — sitemap.xml is URL-discovery-only. Added comments. Deployed extract-gooding

### [ux-audit] CPO full site audit — 13 tasks filed in agent_tasks
- Conducted Playwright-based audit of all major pages: /, /search, /vehicle/[id], /market, /portfolio, /offering, /organizations, /profile
- Confirmed via direct API testing (not just screenshots) — identified root causes not just symptoms
- 3 confirmed P0 broken experiences:
  1. Vehicle profile stuck loading: get_vehicle_profile_data RPC times out (3s) for anon users (task bda3c25b, P97)
  2. /market is a "Coming Soon" hardcoded stub — real data at /market/exchange not linked (task 8aaed8ad, P95)
  3. Homepage Feed tab: "Unable to load vehicles" error — listing_kind column issue in CursorHomepage.tsx (task 0139bb65, P93)
- 10 additional UX issues filed (P68-P90):
  - Search takes 11+ seconds, shows "0 results" while loading (task 6db748af, P90)
  - Nav has no Search or Market links (task 99850151, P88)
  - Search empty state blank (task a2e04f6a, P85)
  - Search filters (Year/Price/Make) not rendering (task c774b1cd, P85)
  - Investor offering gate shows no traction stats (task ac67d3b6, P82)
  - No loading skeleton during search (task b9e49520, P78)
  - No logo/wordmark in header (task 723ab790, P75)
  - Mobile bottom nav missing Search/Market (task 96434c40, P72)
  - Vehicle profile tab labels confusing Evidence/Facts/Commerce/Financials (task da638271, P70)
  - Similar Sales section not wired/visible (task e0433594, P68)
- All 13 tasks filed to agent_tasks as vp-platform, status=pending

### [frontend-ux] Global UX Pass 2 — typography normalization + loading states + empty states
- **pt→px font unit purge**: Eliminated ALL `pt` font-size units across entire frontend (~1900+ occurrences in pages, ~232 component files with pt units). All converted to px with correct pt→px ratios (8pt→11px, 9pt→12px, 10pt→13px, 14pt→19px, 16pt→21px, etc.)
- **AuctionMarketplace**: Replaced bare "Loading auctions..." with 6-card skeleton grid (pulse animation). Fixed 32 pt units.
- **MarketSegments**: Replaced bare "Loading market segments..." with full-page skeleton grid (6 cards with pulse). Fixed 14 pt units.
- **Dashboard**: Replaced bare "Loading..." text with 4 skeleton rows.
- **CursorHomepage**: Replaced "Loading vehicles..." with 6-card skeleton grid.
- **NukeEstimatePanel**: Replaced "Loading..." text with 2-line skeleton.
- **ServiceVehicleCardRich**: Replaced "Loading..." text with skeleton placeholder.
- **MarketFundDetail**: Improved "Fund not found" error state copy.
- **Search.tsx**: Fixed 42px "N" logo on empty state (was 32pt = 42.67px).
- **About.tsx**: Fixed final "NUKE Platform" → "Nuke" branding instance in footer.
- Files changed: ~300+ frontend files. Zero TypeScript errors throughout.
- Commits: 944ba7704 (bulk), 10c63847c (TeamInbox).

## 2026-02-27

### [market] Market Exchange, Fund Detail, Portfolio — comprehensive UX overhaul
- **MarketDashboard** (/market): replaced "Coming Soon" placeholder with live data dashboard — real fund cards from api-v1-exchange, animated skeleton loading, platform AUM stats strip, CTAs
- **MarketExchange** (/market/exchange): skeleton loading (4 animated cards), user-friendly error state with Refresh button (no raw error string), BETA badge properly styled, market cap formatted as $X.XXB/M/K, font sizes → CSS vars
- **MarketFundDetail** (/market/exchange/:symbol): full skeleton loading (no flash of "Fund not found"), not-found state with CTA, removed "MVP: shares issued at NAV" dev note visible to investors, shares preview calculation, sign-in CTA for anon users, NAV hero strip, error/success use --error-dim/--success-dim backgrounds
- **Portfolio** (/market/portfolio): h1/value cards use proper font sizes (var --fs-12), tabs refactored from 8 copy-paste blocks to single data-driven loop, empty shares state has "Browse Funds" CTA, removed alert() from org stocks click, raw px → CSS vars throughout
- Commit: b9ae1497c

### [yono] Zone classifier live + Bearer token auth + interior_quality — VP AI session
- **Zone classifier uploaded to Modal**: yono_zone_head.safetensors (2.1MB), yono_zone_classifier_labels.json, yono_zone_config.json → `yono-data /models/`
- **Zone classifier integrated in modal_serve.py**: `_load_zone_classifier()` loads ZoneClassifierHead (768→512→256→41 zones); used in both `_analyze_finetuned` and `_analyze_zeroshot` via `_classify_zone(features)` on shared Florence-2 encoder output
- **Health endpoint**: now reports `zone_classifier: true, zone_classes: 41`
- **zone_source field**: `zone_classifier_v1` (when ZoneClassifierHead active) vs `photo_type_heuristic` (fallback)
- **DB migration applied**: `interior_quality smallint` + `zone_source text` added to vehicle_images (applied via port 5432, NOT VALID check constraint)
- **yono-vision-worker updated**: now writes `interior_quality` and `zone_source` to vehicle_images on every analysis
- **Bearer token auth**: `nuke-sidecar-secrets` Modal secret created, token stored in Supabase secrets + .env; `auth_middleware` added to modal_serve.py (GET /health exempt); yono-classify, yono-analyze, yono-vision-worker all pass `Authorization: Bearer $MODAL_SIDECAR_TOKEN`
- **Verified**: GET /health → 200 (no auth), POST /classify no token → 401, POST /classify with token → 200
- **Upload script rewritten**: `yono/scripts/upload_tier2_to_modal.sh` now includes zone files, --zone-only, --no-deploy flags, auto-runs `modal deploy` after upload
- **Tasks completed**: ba1593fd (TTLRM eval, NO-GO), b6b693ab (Bearer auth, DONE)
- **Training status**: German tier-2 running (PID 28401, epoch 4/25), watcher PID 7390 waiting; zone classifier DONE (72.8% val_acc)

### [deal-flow] Transfer system wiring + suppress_notifications — VP Deal Flow 2026-02-27
- **suppress_notifications (P78 COMPLETED)**: transfer-automator seed_from_auction + seed_from_listing now accept suppress_notifications param. backfill_transfers_for_sold_auctions DB function updated to always pass suppress_notifications:true. Both deployed.
- **Crons 223-227**: Still paused. Email blast risk eliminated. Re-enable ONLY after Twilio working (CFO task P92). Command: UPDATE cron.job SET active = true WHERE jobid BETWEEN 223 AND 227;
- **stripe-webhook wired**: checkout.session.completed with purchase_type=vehicle_transaction now calls transfer-advance:advance_manual for payment_confirmed milestone. Deployed.
- **vehicle_transactions.ownership_transfer_id**: UUID FK column added (Management API). Migration 20260227120000. Links Stripe fee record to parent ownership_transfer.
- **get_transfer bug fixed**: Was "{error: '[object Object]'}" — now uses error.message. Deployed.
- **Twilio diagnosis**: .env has placeholders → Supabase secrets set to placeholders → 401 on every SMS. Filed CFO task (P92).
- **ownership_transfers schema**: inbox_email, buyer/seller_access_token, buyer/seller phone/email columns exist (deployed outside migration tracking — added doc migration 20260227110000).

### [frontend] Vehicle profile page — comprehensive UX quality pass — commit 475c6ce1b
- VehicleProfileTabs: rewrote tab bar with human-readable labels (Overview/Media/Specs/Comps/Taxonomy/Bids), URL deep-linking via ?tab=, hover states, comps count badge
- VehicleComparablesTab: fixed double padding (card wrapper + SimilarSalesSection both had padding)
- VehicleDescriptionTab: replaced hardcoded 320px grid column with responsive CSS classes
- VehicleSpecsTab + VehicleTaxonomyTab: 'Not specified' null fallback → '—'
- VehicleMediaTab: added flex column layout
- VehicleBasicInfo: replaced noisy red MISSING badge for transmission/mileage/color with muted 'Unknown' (VIN/Year keep MISSING — identity fields)
- VehicleHeroImage: SVG placeholder when no photo; image container dark bg uses design token
- SimilarSalesSection: fixed '0d ago' bug (now 'Today'/'Yesterday'), improved empty state, added container padding, fixed skeleton height
- VehicleProfile: replaced hardcoded colors (#1a1a1a, #333, #999) with design tokens; back button navigates(-1) not wrong route

### [frontend] Org profile + offering page UX improvements — commit d24aa0ad0
- InvestorOffering (/offering): replaced bare access-code gate with compelling landing showing 4 key stats, value prop headline, competitor context strip; added "Contact to Invest" CTA in portal header; fixed tab overflow; increased body text to 10pt; updated YONO status to reflect Phase 5 + deployed sidecar
- OrganizationProfile (/org/:id): removed "Business docs" red button from all orgs (only owners now); skeleton loading state; toast notifications replacing all alert() calls; fix tab font var; verification badge in header
- MarketCompetitors (/market/competitors): split CTA into trade + investor inquiry cards with /offering link

### [docs] SDK README + OpenAPI + Quickstart — VP Docs
- Rewrote `tools/nuke-sdk/README.md` (v1.4.0): install, 3 quick examples (search, vision, signal), full API reference for all 14 resources, types table, rate limits, error handling, changelog link
- Fixed `docs/api/openapi.yaml`: Vision paths were misplaced inside `components` section — moved to proper `paths` block. Added `api-v1-export` + `api-v1-exchange` endpoints. Added `MarketFund` + `VehicleOffering` schemas. Bumped spec version to 1.4.0. Now 21 documented paths, 29 operationIds.
- Created `docs/QUICKSTART.md`: zero-to-first-call guide with VIN lookup, comps, batch vision, signal scoring, bulk export, error handling, rate limits, REST API examples

### [extraction] BaT extraction queue unblocked — 119,300 pending items now draining
- Root cause: `process-bat-extraction-queue` edge function was NOT deployed (returned 404/NOT_FOUND on all invocations)
- `aggressive-backlog-clear` cron (job 65, every 10min) was firing correctly but hitting dead endpoint
- Fix: Deployed `process-bat-extraction-queue` via `supabase functions deploy`
- Added dedicated cron job 260 (`bat-extraction-queue-worker`, `*/2 * * * *`) for more frequent firing
- Confirmed function now processes: `{"success":true,"processed":1,"completed":1}` on first invocation
- Queue: 119,300 pending items, oldest Dec 20, 2025. Drain rate: ~36/hr from crons (function processes 1 item/call by design)
- Note: `claim_bat_extraction_queue_batch` RPC provides atomic claim preventing double-processing

### [extraction] PCarMarket URL slug YMM fallback — deployed
- Problem: 50 items/run failing with "Missing required fields (year, make, model)"
- Root cause: `parsePCarMarketIdentityFromUrl()` only matched `/auction/YEAR-slug` pattern, not `/marketplace-YEAR-make-model`
- Fix: Added second regex in `parsePCarMarketIdentityFromUrl()` — tries `/marketplace-(\d{4})-(.+?)` if `/auction/` pattern fails
- Handles compound makes (land rover, mercedes-benz, aston martin, alfa romeo, rolls-royce) correctly
- Example: `/marketplace-2005-land-rover-range-rover` → `{ year: 2005, make: 'land rover', model: 'range rover' }`
- Deployed: `import-pcarmarket-listing` via `supabase functions deploy`
- File: `supabase/functions/import-pcarmarket-listing/index.ts` (lines 202-206)

### [frontend/perf] Auth waterfall elimination — commit 05000c396
- Created `nuke_frontend/src/contexts/AuthContext.tsx`: single global `getSession()` at app boot, initialised synchronously from localStorage (Supabase `sb-{ref}-auth-token`). Returns `loading=false` on first render for returning users.
- Updated `useAuth` hook: now reads from AuthContext, zero network calls per mount
- Updated `useSession` (AppLayout): delegates session/loading to AuthContext, profile fetch only
- Wrapped `App.tsx` in `<AuthProvider>` as outermost provider
- Fixed 14 pages: Vehicles, DeveloperDashboard, AddVehicle, InvoiceManager, ApiKeysPage, MarketSegments, MarketFundDetail, SocialWorkspace (7 inline getSession calls), DataDiagnostic, DealerBulkEditor, Dashboard, Search, RestorationIntake, Profile
- Before: N pages x async getSession() waterfall per mount. After: 1 getSession() at app start, all pages read from context synchronously

### [cfo] CFO session — Twilio diagnosis + pipeline unpause + token budget — 2026-02-27
- Twilio 401 root cause: NOT negative balance. Credentials were never configured — .env has placeholder values ("your-twilio-account-sid"). Twilio error 20003: invalid username.
- Filed P88 task to COO for founder action (real Twilio account + credentials required). SMS cost estimate: $0.0079/SMS, 150K backfill = ~$1,185.
- Claimed and completed pre-existing CFO Twilio task (id: f49f82f7).
- Filed P80 CEO memo (via COO): Unpause analyze-image in YONO-first hybrid mode. Cost: $3,250 total capped ($50/day x 65 days), $150/month ongoing. Vs $2,000/month cloud-only. Wait for PIDs 7241+7390 to finish, then remove NUKE_ANALYSIS_PAUSED.
- Filed P75 CTO recommendation: ralph-spawn token budget — Haiku for workers ($0.056/task), Sonnet for VPs ($0.525/task), Opus for strategy ($5.25/task). 22-task run at mixed model = ~$14 vs $115 all-Opus. Annual savings vs all-Opus: ~$72K.
- Updated CFO cost model in .claude/CFO_IMAGE_PIPELINE_COST_MODEL.md (prior version already comprehensive — no changes needed).

### [frontend] Map bug fixes — 2026-02-27
- Removed Math.random() jitter from UnifiedMap.tsx geo() — replaced with deterministic hash-based offset (simpleHash). Same location always renders at same spot. Commit 1ad6c89c7.
- Added custom cluster icons (blue/white for vehicles, amber/black for query) via makeClusterIcon() + iconCreateFunction prop. Eliminates black-on-black cluster count bubble visibility issue.
- GPS priority was already correct (gps_latitude first, geo() fallback). Verified and left intact.
- Fixed pre-existing bug: businesses Supabase select was fetching 'type' column (doesn't exist) instead of 'entity_type'.

### [coo] Executive triage + work order routing — 2026-02-27 11:30 UTC
- Reviewed all VP inboxes (all empty)
- Confirmed YONO training: zone classifier DONE (72.8% val_acc), german tier-2 epoch ~5/25, watcher PID 7390 active
- Task snapshot: 19 pending, 3 in_progress (VP-AI ONNX upload, VP-Photos brief, curator dedup)
- Filed 5 new work orders:
  - f49f82f7: CFO P90 — Twilio negative balance blocking transfer SMS
  - 9fb1563a: VP-Extraction P80 — RM Sotheby's individual listing scraper
  - 87446ee0: VP-Extraction P80 — Gooding individual listing scraper
  - 6deef460: VP-Deal-Flow P78 — add suppress_notifications before re-enabling backfill crons
  - d4149eb7: VP-Platform P75 — Transfer System UI (operator dashboard + buyer/seller pages)
- Cancelled duplicate ONNX task be95e3aa (fdf5038f already in_progress)
- Key gap identified + filed: FB Marketplace probe had no task — filed 62f30b2e (VP-Extraction P82) for logged-out GraphQL path probe
- Note: VP Extraction already active on RM Sotheby's (per ACTIVE_AGENTS.md) — 9fb1563a is redundant, will self-resolve

### [cto] Architecture review + work orders — 2026-02-27 11:30 UTC

Filed 7 agent_tasks from CTO architecture review:
- P80 vp-platform: ralph-spawn token budget controls (MODEL_MAP, --max-tokens-per-agent, --session-budget, Opus cap 3, token logging)
- P75 vp-ai: YONO Modal sidecar Bearer token auth (modal_serve.py middleware + yono-classify + yono-analyze updated)
- P70 vp-extraction: crawl-bat-active archiveFetch violation fix
- P70 vp-extraction: sync-live-auctions archiveFetch violation fix
- P60 vp-extraction: extract-gooding sitemap fetch audit
- P55 vp-extraction: source-census audit (classify as acceptable health-check or fix)
- P50 vp-platform: Agent type registry audit + remap

Processed CFO cost model task (bcf6d537): CTO approved model tiering (Haiku=workers, Sonnet=VPs, Opus=exec). Deferred model_hint DB column — MODEL_MAP in code sufficient. Added Opus concurrency cap of 3 to work order.

### [extraction] FB Marketplace GraphQL probe — 2026-02-27 07:20 UTC

**Finding: Logged-out GraphQL works from residential IPs, blocked from Supabase datacenter IPs.**

Key results:
- `doc_id: 33269364996041474` with `viewer.marketplace_feed_stories.edges` — CONFIRMED WORKING from residential
- LSD token extractable from marketplace HTML (changes per request, session-specific)
- 24 listings per page, full pagination via `end_cursor`, zero overlap between pages
- Tested: Austin TX, Seattle WA, Chicago IL — all work with 24 listings
- Datacenter IP block: `Rate limit exceeded (1675004)` — IP-level, not session-level
- FB serves 1.1MB to residential, 460KB stripped response to datacenter IPs
- `vehicle_info` field NOT returned in logged-out GraphQL (year/make/model must be parsed from title)

Existing infrastructure confirmed working:
- `scripts/fb-marketplace-local-scraper.mjs` — local scraper (GraphQL + 43 metro areas configured)
- `scripts/fb-relay-server.ts` — relay architecture exists, relay currently offline

Created: `facebook-marketplace-extraction.md` — full technical reference with 3 paths forward

### [platform] Platform health sprint — 2026-02-27 05:30 UTC

**Stubs from inventory (P97 — task d1c9187e):**
- 24K stub vehicles (no year/make/model) were leaking into public search
- Fixed search edge function ilike fallback (added YMM null filters)
- Applied migration 20260227060000 — updated search_vehicles_fulltext, search_vehicles_fuzzy, search_vehicles_fts
- Created vehicles_inventory view (is_public=true AND year/make/model NOT NULL)
- Fixed Search.tsx nearby query to filter YMM nulls
- Deployed search + universal-search edge functions

**Quality backfill timeout fix (P85 — task b769a800):**
- Workers 237-240 timing out every run (batch 150-300 rows, JOIN on temp table = 2min lock wait)
- Fix 1: Reduced batch size to 50 rows, switched from JOIN to = ANY(array)
- Fix 2: Added SET LOCAL lock_timeout = '5s' + EXCEPTION handler to fail fast on contention
- All 4 workers now succeeding: W1=<15s, W2=~17s, W3=~32s, W4=~48s
- Rate: ~12K rows/hour across 4 shards (queue draining in parallel)

**DB load / cron cleanup (P78 — task 946fdae8):**
- Deactivated 3 crons causing heavy DB load:
  - treemap-refresh (job 175): 10x CONCURRENT mat view refreshes, each 17min — every 30min = always failing
  - auto-duplicate-cleanup (job 43): hitting statement timeout 3/4 runs
  - dedup-vehicles-batch (job 258): lock contention on vehicle_images + vehicles, 100% fail rate
- Fixed reconcile_listing_status(): reduced batch 50→10 items, removed SET LOCAL statement_timeout (doesn't override pg_cron parent timeout)
- Net result: 3 fewer constant statement timeouts every 10-30 minutes

### [intel] Similar Sales feature — vehicle profile Comps tab — 2026-02-27
- Built `SimilarSalesSection.tsx` — card grid showing 5-20 comparable sold vehicles
  - Platform badges (Bring a Trailer, Barrett-Jackson, Mecum, etc.) with brand colors
  - Sold date (relative: "2yr ago"), mileage, thumbnail image, listing URL
  - Summary stats bar: avg/median/range price across all comps
  - Show more/fewer toggle at 6+ results
- Enhanced `api-v1-comps` edge function:
  - New param: `vehicle_id` (resolves canonical make/model/year via pk lookup)
  - Added `auction_events` as primary data source via `get_auction_comps()` DB function
  - `get_auction_comps()`: plpgsql JOIN of vehicles+auction_events, uses `idx_vehicles_make_model` + `idx_auction_events_vehicle`, 8s internal timeout
  - Calls RPC via direct `fetch()` to PostgREST (avoids Supabase JS client timeout issues)
  - Fallback: `vehicles.sale_price` for records without auction events
  - Performance: 0.6s (make/model/year params), ~3.5s (vehicle_id with pk lookup)
- Updated `VehicleComparablesTab.tsx`: Similar Sales section first, user-submitted comps below
- `get_auction_comps` DB function created (SECURITY DEFINER, plpgsql, 8s timeout)

### [platform] Stub vehicle filter — inventory accuracy fix — 2026-02-27
- Problem: ~97K stub vehicles (is_public=true, no year/make/model) polluting all search/inventory
- Solution: Added `year/make/model IS NOT NULL` filter to all inventory read paths
- DB: Updated `search_vehicles_fts`, `search_vehicles_fulltext`, `search_vehicles_fuzzy` functions
- DB: Created `vehicles_inventory` view (public vehicles with minimum data — use for future queries)
- Edge functions deployed: `api-v1-search`, `api-v1-vehicles`, `universal-search`
- Frontend: `IntelligentSearch.tsx` autocomplete now filters stubs
- Migration: `20260227060000_filter_stub_vehicles_from_inventory.sql`
- Audit findings by platform: C&B 99.9%, Barrett-Jackson 99.9%, BaT 94.3%, Mecum 91.8%,
  Bonhams 19.1% (extraction sprint ongoing), User Submission 13.5% (expected)
- Stubs remain in DB and surface automatically once extraction fills YMM
- Tasks completed: d1c9187e (P97 vp-platform), 3827a50b (P85 cdo audit)
- Commit: 5257d97f9

### [extraction] CL asking price backfill + queue assessment — 2026-02-27 05:00 UTC
- Built and deployed `backfill-cl-asking-price` edge function
  - Scrapes individual CL listing pages to extract asking price via `<span class="price">` and JSON-LD
  - 500ms delay between requests (CL rate limit avoidance)
  - Handles expired listings (410) gracefully, rejects junk prices ($1 placeholders)
  - Triggers batch-market-proof after successful updates
- Ran 10 batches of 25 entries = 250 entries processed
  - 97 null prices → prices restored (190 → 93 remaining, 51% reduction)
  - 93 remaining: ~60 expired 410s, ~25 $1 placeholder prices (unfixable), ~8 rate-limited
- Created cron job 259 (daily 6 AM UTC) to keep CL prices current
- Completed 2 agent_tasks: c8259c99 + 041380bf (queue backlog assessment)
  - Actual drain rate: 3,793/hr (not 384/hr as estimated — that was per-worker, not system total)
  - ETA to clear backlog: ~25h (not 91h)
  - BaT nearly complete (144 pending), MecumLive 33.8K, C&B 27K, B-J 15.4K

### [yono] Zone classifier + tier2 watcher restarted — 2026-02-27 04:52 UTC
- Zone classifier (PIDs 12814+39959) were dead since last session
- Added --resume flag to yono/scripts/train_zone_classifier.py (loads head+optimizer state, advances LR schedule)
- Resumed zone training from epoch 10 checkpoint: PID 7249/7241, epoch 11/15, best_val_acc=72.8%
- Restarted tier2 watcher: PID 7390, watching zone PID 7241, will train german/british/japanese/italian/french/swedish + ONNX export
- YONO sidecar (Modal): confirmed operational via edge function test; redeployed for freshness. Direct curl from dev machine gets 404 (Modal IP restriction) but edge functions work fine.
- Vision workers 247+248 confirmed active and succeeding every 2 min
- iPhoto library scan (PID 23805): completed 2026-02-25, results in yono/library_scan/scan_results.json

### [platform] INCIDENT fix: bat-snapshot-parser statement timeout (jobs 173/174) — 2026-02-27 03:43 UTC
- Root cause: `parse_bat_snapshots_bulk()` cursor scanned 367K rows (59GB table) to find 291 unprocessed rows — `(metadata->>'parsed_at') IS NULL` filter had no index; pg_cron's 120s timeout killed every run before any row was processed
- Fix: created partial index `idx_lps_bat_unparsed_fetched` (16KB, covers only unparsed BAT rows) → query plan switched from SeqScan to Index Scan
- Also reduced batch size 300→100 in cron jobs 173/174 for safety margin
- Migration: `20260227040000_bat_snapshot_parser_index_fix.sql`

### [cwfto] Situational brief — 2026-02-27 03:40 UTC
- 1.25M vehicles, 101K import queue pending, 18.5% quality backfill (231K/1.25M)
- Zone classifier PID 12814 alive at epoch 9/15 (~3hrs remaining); replied to COO watchdog
- YONO sidecar unreachable (vp-ai task P85 in_progress)
- DB statement timeouts on simple queries — under heavy extraction + backfill load
- Filed 3 follow-up tasks: DB load investigation (vp-platform P78), queue backlog verification (vp-extraction P78), dedup incident tasks (vp-platform P30)
- Scheduled next CWFTO loop (P92)

### [db] observation_sources completeness audit — COMPLETED 2026-02-27
- Audited all active sources (auction_events, listing_page_snapshots) against observation_sources
- Found 2 missing: `collecting-cars` (122 auction_events, collecting-cars-discovery edge fn) and `broad-arrow` (1 event, extract-broad-arrow edge fn)
- Added both with base_trust_score=0.80, category=auction
- Documented 4 slug normalization mismatches in notes (bringatrailer→bat, cars_and_bids→cars-and-bids, hagerty→hagerty-marketplace, ecr→exclusive-car-registry)
- Total sources: 90 → 92

### [platform] mecum-live-queue-worker connection pool incident — COMPLETED 2026-02-27
- INCIDENT: jobs 251-255 (mecum-live-queue-workers 1-5) experiencing ~50% startup timeout failures
- Root cause: 40 active minute-frequency crons saturating connection pool
- mecumlive queue: 34k pending items (NOT empty — workers genuinely needed)
- Fix: deactivated workers 3, 4, 5 (jobs 253, 254, 255) — kept workers 1 and 2 active
- Total active minute-frequency crons reduced: 40 → 37
- Net throughput unchanged: 2 reliable workers = 5 workers at 50% failure rate

### [docs] OCR pipeline startup brief + stale-lock bug fix — COMPLETED 2026-02-27
- Pipeline status: 259 complete, 656 skipped, 1 pending (unlocked), 0 failed
- 50% of complete items linked to vehicles; 0 deals linked (link-document-entities not matching deals)
- Skipped breakdown: 653 low-confidence `other`, 3 vehicle-image false-positives (no deal_document_id), 3 real docs (2 registration + 1 title) at confidence 0-15 — flagged for manual review
- Fixed bug: stale-lock cleanup cron (job 256) was missing `pending` status — a locked-pending item could never self-recover. Fixed to include `pending` in the covered statuses.
- Manually unlocked stale receipt item `69dc746e` (locked since 02:17 UTC, over 1h stale)
- Vault (vault_attestations): 0 entries — not yet populated
- Both OCR crons active and healthy: job 250 (worker-batch, */5min), job 256 (stale-lock-cleanup, */3min)

### [worker] Exponential backoff for failed extractions — COMPLETED 2026-02-27
- Added retry logic to `process-import-queue` failure paths (extractor failure + catch block)
- Transient errors (timeout, rate_limited, blocked): 10 min base delay × 2^attempts, max 8 attempts, cap 2 hours
- Non-transient errors (extraction_failed, browser_crash, bad_data): 5 min base × 2^attempts, max 5 attempts, cap 2 hours
- Non-vehicle pages (skipped) remain terminal (no retry)
- Increased `p_max_attempts` in claim from 3 → 8 to allow retries to run
- `next_attempt_at` set on retry; claim RPCs already respect it (WHERE next_attempt_at IS NULL OR next_attempt_at <= NOW())
- `continuous-queue-processor` already had full backoff — no change needed there
- Deployed: `process-import-queue`

### [worker] BAT extractor consolidation — COMPLETED 2026-02-27
- Canonical flow confirmed: `complete-bat-import` → `extract-bat-core` + `extract-auction-comments`
- Fixed `extract-premium-auction`: was routing bat/bringatrailer to deprecated `bat-simple-extract`, now routes to `complete-bat-import`
- Fixed `crawl-bat-active`: was calling `bat-simple-extract` directly, now calls `complete-bat-import`
- Updated `_shared/approved-extractors.ts`: added `bat-simple-extract` and `bat-extract` to `DEPRECATED_BAT_EXTRACTORS`; added `ENTRY: 'complete-bat-import'` to `APPROVED_BAT_EXTRACTORS`
- Updated `TOOLS.md`: corrected 3 references that pointed to deprecated `bat-simple-extract`
- Deployed: `extract-premium-auction`, `crawl-bat-active`
- Note: `bat-extract` and `bat-simple-extract` functions still exist (not deleted) but all live callers now route to `complete-bat-import`

### [vp-platform] API bulk export endpoint — COMPLETED 2026-02-27
- Deployed `api-v1-export` edge function at `/functions/v1/api-v1-export`
- Formats: `format=csv` (attachment), `format=json` (paginated), `format=ndjson` (streaming-friendly)
- Parquet: returns helpful 422 with pandas conversion hint (`pd.read_json(..., lines=True).to_parquet(...)`)
- Cursor-based pagination via `?cursor=<last_id>` — O(1) vs OFFSET, scales to full dataset
- Rate limits: service-role 100K rows, API key 10K rows, user JWT 5K rows per request
- Field selection: `?fields=id,year,make,model,vin,sale_price` (24 fields available)
- All filters: make, model, year/year_min/year_max, price_min/max, vin, transmission, mileage_max, drivetrain, body_style, quality_min
- Unlocks Priya's $200-800/month enterprise tier. Task 4ae51478 completed.

### [vp-extraction] Scrapling Evaluation — NO-GO — COMPLETED 2026-02-27

- **Question**: Should we adopt Scrapling (adaptive selectors, StealthyFetcher, Camoufox) for extraction pipeline?
- **Verdict: NO-GO**. Three decisive reasons:
  1. **Language mismatch**: Python-only. Our pipeline is 100% Deno/TypeScript edge functions. Requires separate Python microservice (Modal/Railway) = new infra + latency + failure mode.
  2. **Wrong failure mode**: Our extractors fail on JSON/API structure changes, not CSS selector breaks. Bonhams uses JSON-LD; Mecum uses `__NEXT_DATA__` JSON. Scrapling's adaptive selectors don't help.
  3. **StealthyFetcher economics**: `archiveFetch()` cache-first already makes Firecrawl cheap. Python StealthyFetcher service would cost more than the Firecrawl it replaces.
- **Revisit**: Python forum scraper (Rennlist, TheSamba) OR Scrapling v1.0 stable.
- Task 9080e841 completed in agent_tasks.

### [vp-orgs] Startup brief / domain audit — COMPLETED 2026-02-27
- 4,003 orgs: 1,831 collection, 1,729 other, 107 dealer, 75 auction_house
- Critical gaps identified: organization_seller_stats (1 entry, stale Feb 14), organization_inventory (0 rows), classic_seller_queue (109 pending, no cron processor), ECR data (45 days stale, no refresh cron)
- Working: enrich-organizations-daily (job 69), seller-intel-rollup (job 214, every 4h), bat-seller-monitor-sweep (job 166, every 6h)
- Sellers extremely thin: 7 pipeline_sellers, 9 seller_sightings total, 0 org-to-seller linkage
- Needs: cron for compute-org-seller-stats, cron for classic_seller_queue drain, ECR refresh schedule, org-to-seller bridge

### [vp-platform] Search UI: Fix F tier / 0 observations — COMPLETED 2026-02-27

- **Root cause**: universal-search returned only year/make/model in metadata; VehicleCardDense calculated F tier for all results
- **universal-search**: Added 20+ vehicle fields to SELECT; FTS path now enriches limited RPC results with second IN query; `buildVehicleMetadata()` uses comment_count→event_count proxy, primary_image_url→image_count
- **SearchResults.tsx**: Passes vin, sale_price, current_value, asking_price, mileage, transmission, profile_origin, ownership_verified, view_count, image_count, event_count to VehicleCardDense; list view shows key specs row (price, VIN, mileage, transmission)
- **Result**: BaT imports with comments now score C/B tier; vehicles with VIN+price score D/E; images display when primary_image_url is set
- Deployed to Supabase. Commit: 2ffdb4a6d

### [cpo] SDK v1.4.0 — nuke.signal.score() — COMPLETED 2026-02-27

- **`api-v1-signal` edge function** deployed to Supabase. GET by `vehicle_id` or `vin`.
- Reads from `nuke_estimates` (521K rows, 8.3K with deal_score, all 521K with heat_score).
- Computes `price_vs_market` live: `(asking_price - estimated_value) / estimated_value * 100` (negative = below market = good deal).
- Derives `comp_count` from `signal_weights.comps.sourceCount`.
- Translates internal labels (`plus_3` → `strong_buy`, `minus_3` → `overpriced`) to consumer-facing names.
- Returns 404 with actionable hint when no estimate exists.
- **SDK changes**: `signal.ts` resource + `SignalScore`/`SignalScoreParams` types + wired into `Nuke` client.
- **Version**: `@nuke1/sdk` bumped `1.3.1` → `1.4.0`.
- **Docs**: `CHANGELOG.md` created, `openapi.yaml` updated with `/api-v1-signal` path + `SignalScore` schema.
- **Validated**: live endpoint returns correct data (2006 LR3, $600 sale price, $7100 estimated, -91.55% below market ✓).

### [vp-platform] P0: Search/API Filtering Completely Broken — FIXED 2026-02-27

**Root cause 1 — api-v1-vehicles**: `?make=Porsche&model=911&year=1973` params were read but **never applied** as query filters. Fixed by adding full filter chain: `make`, `model`, `year`, `year_min`, `year_max`, `vin`, `price_min`, `price_max`, `transmission`, `mileage_max`, `sort`, `sort_dir`.

**Root cause 2 — universal-search**: FTS "strategy 2" (raw `search_vector @@ to_tsquery`) at relevance=0.8 returned noise (e.g. "997" matching Austin-Healey Sprite 997cc descriptions); filtered to relevance >= 0.85. Over-aggressive year+make+model dedup collapsed distinct cars — replaced with ID-only dedup. Always-run ILIKE fallback merged with FTS for reliable make/model matching.

**Verified**: `?make=Porsche&model=911&year=1973` → 665 correct results; "porsche 997 gt3" → actual GT3s; "Ford" → 113K Fords.
- Files: `supabase/functions/api-v1-vehicles/index.ts`, `supabase/functions/universal-search/index.ts`

### [vp-platform] P1: Search Filters — COMPLETED 2026-02-27

- Added vehicle search filters to `Search.tsx` (task 212b6ecc)
- **Filter panel**: price range (min/max), year range, max mileage, transmission (auto/manual/any), for-sale vs sold toggle — appears whenever vehicle results are present
- **Enrichment**: post-search Supabase query fetches `sale_price, mileage, transmission, is_for_sale, city, state` for all vehicle result IDs; merged into result metadata
- **Filtering**: client-side, computed via `useMemo` on enriched results; active filter count badge + "Clear all" button
- **Sort**: added Price (asc/desc) and Year (asc/desc) options to `SearchResults.tsx` sort dropdown
- TypeScript clean (tsc --noEmit passes)
- Files: `nuke_frontend/src/pages/Search.tsx`, `nuke_frontend/src/components/search/SearchResults.tsx`

### [vp-platform] P0: Market Dashboard timeout — COMPLETED 2026-02-27

- `MarketDashboard.tsx` was querying `market_segments_index` view directly → statement timeout every load
- Investor (James) had rejected platform based on the broken page ($0 AUM + timeout error)
- Fix: replaced entire page with professional "Coming Soon" placeholder — no DB queries, no errors
- Route `/market` and `/market/dashboard` still live, CTA buttons link to working `MarketExchange` page
- Task 4317301c marked complete in agent_tasks

### [vp-platform] Platform Health Check + Cron Config Fixes — COMPLETED 2026-02-27 ~03:00 UTC

**Health Summary:**
- 160 cron jobs total (146 active, 14 intentionally inactive)
- Zero stale queue locks
- Quality backfill workers 237-240: ACTIVE, making progress (~97K rows across 4 shards, ~1.05M remaining)
- Import queue: 102,911 pending, actively processing

**Fixed 4 broken cron jobs** (all using stale `current_setting()` config — `app.supabase_url`/`app.service_role_key`/`app.settings.*` not set in DB):
- Job 213 (exchange-pricing-cycle): Was returning NULL URL → fixed to hardcoded URL + `get_service_role_key_for_cron()`
- Job 235 (agent-monitor-scan): Was throwing "unrecognized config param" → fixed same way
- Job 186 (paper-trade-autopilot): Same broken pattern → fixed
- Job 128 (auto-sort-telegram-photos): Same broken pattern → fixed

**Incident tickets filed:**
- P70: bat-snapshot-parser-continuous (jobs 173/174) — ~19% failure rate from statement timeout in `parse_bat_snapshots_bulk()`
- P60: mecum-live-queue-workers (251-255) — ~50% failure rate from connection pool saturation (45 minute-frequency crons total)

### [worker] Extraction Metrics Logging — COMPLETED 2026-02-27

- Created `extraction_metrics` table: per-invocation rows with extractor_name, source, run_id, source_url, vehicle_id, success, latency_ms, error_type, error_message, http_status
- Created `extraction_metrics_hourly` view: hourly rollups with success rate %, avg/p50/p95 latency, and jsonb error_breakdown per extractor+source
- Created `extraction_metrics_24h` view: 24h health summary ordered by failure count
- Created `supabase/functions/_shared/extractionMetrics.ts`: `ExtractionMetricsLogger` class (startItem/recordSuccess/recordFailure/flush), `logExtractionMetric` quick helper, `categorizeError` function
- Updated `continuous-queue-processor`: uses `ExtractionMetricsLogger` per extractor, times each item fetch, records success/failure with categorized error type and HTTP status, batch-flushes to DB at end of run
- Migration: `supabase/migrations/20260227020000_extraction_metrics.sql`

### [vp-extraction] Extraction Queue Snapshot + Next Optimization Target — COMPLETED

**Queue Depths (02:50 UTC Feb 27)**

| Source     | Pending | Rate/hr | ETA      | Error Rate        |
|------------|---------|---------|----------|-------------------|
| mecum      | 16,934  | 521     | ~33 hrs  | 2 failed (~0%)    |
| b-j        | 17,966  | 626     | ~29 hrs  | 0 failed          |
| pcarmarket | 2,587   | 128     | ~20 hrs  | 50 failed (1.9%)  |
| bat        | 1,603   | 745     | ~2.2 hrs | 2 failed (~0%)    |
| bonhams    | 14      | 43      | ~0.3 hrs | 0 failed          |
| gooding    | 15      | 113     | ~0.1 hrs | 2 failed          |
| c&b        | 0       | —       | CLEARED  | —                 |

**Description Coverage (sample of 50 recent items per source)**
- mecum: 100% — Phase 2 fix verified working
- BaT: 100%
- PCarMarket: 100%
- B-J: 44/48 = 91.7%
- Bonhams: 20/22 = 90.9%
- Gooding: not measurable via queue (vehicle_id not written back to import_queue rows)
- C&B: not measurable (queue cleared)

**Secondary Finding: bat_extraction_queue stalled**
- 119,160 pending items, 0 processing — oldest items from Dec 20, 2025 (2+ months idle)
- `process-bat-extraction-queue` function exists but no active cron firing it
- Step 2 of BaT pipeline (comment extraction) completely stalled

**Next Optimization Target: PCarMarket URL-slug fallback parsing**
- 50 failures all "Missing required fields (year, make, model)"
- Year/make/model IS in the URL slug: e.g. `/marketplace-2005-land-rover-range-rover`
- Fix: add URL slug regex fallback in `import-pcarmarket-listing` before quality gate

## 2026-02-26

### [worker] Rate limiting on public endpoints — 2026-02-26
- Created `supabase/functions/_shared/rateLimit.ts` — reusable fixed-window rate limiter backed by Postgres
- Migration `20260226250000_rate_limits_table.sql`: `rate_limits` table + `rate_limit_increment()` SECURITY DEFINER RPC + `rate_limits_cleanup()`
- `universal-search`: 60 req/min per IP (60s window)
- `map-vehicles`: 120 req/min per IP (60s window — higher for map tile interactions)
- Fail-open on DB errors (never blocks users due to RL infra issues)
- Adds `X-RateLimit-Limit`, `X-RateLimit-Remaining`, `X-RateLimit-Reset` headers to all responses
- Returns 429 with `Retry-After` when limit exceeded
- Both functions deployed

## 2026-02-27

### [cdo] Data Quality Audit — 2026-02-27
- **Scale confirmed**: 1,254,455 vehicles (pg_class), 33,742,616 images, 11.6M auction comments
- **Quality backfill progress**: 100,200 vehicles scored across 4 workers (8% of corpus). Scored vehicles trend 80-86/100 avg — scoring function is well-calibrated.
- **Score distribution** (gooding, fully scored 369 vehicles): p25=80, p50=90, p75=90, p90=90 — high scores when data present
- **Cross-source averages**: gooding 86.2, barrett-jackson 83.3, mecum 79.9
- **Grade F sources**: bonhams (25,202 vehicles, 12.4% YMM — worst single source), ecr_collection_text (24,995 vehicles, 0.04% YMM), forum_build_extraction (9,321 vehicles, 4.3% YMM), thesamba (83 vehicles, 49.4% YMM)
- **Grade D**: facebook_marketplace (3,655 vehicles, 60.1% YMM coverage)
- **Missing fields across all sources**: ~92K null year, ~25K null make, ~28K null model — dominated by bonhams + ecr_collection_text + __unknown__ source
- **Top 3 levers**: (1) Bonhams YMM re-parse (+22K scoreable vehicles), (2) backfill completion ETA ~30hr, (3) ecr_collection_text/forum_build cleanup or YMM extraction from text

### [worker] Health check endpoint — 2026-02-27
- Deployed `supabase/functions/health` edge function (no-verify-jwt)
- 3 parallel checks: DB connection ping, recent extractions (last 1h + 24h with rate drop detection), queue depth (pending/processing/stuck with high-depth warn)
- Returns `status: ok|degraded|down` + structured per-check detail JSON
- HTTP 200 for ok/degraded, 503 for down
- Validated: DB ok 516ms, 182 extractions/last-1h, queue=113k items (degraded, matches known backlog)

### [vp-ai] YONO sidecar URL verification + fix — 2026-02-27
- **Root cause found**: URL typo — `sss73133` (wrong) vs `sss97133` (correct) Modal workspace slug
- **Sidecar confirmed alive**: `https://sss97133--yono-serve-fastapi-app.modal.run/health` → 200 OK, `uptime_s=696`, `vision_mode=finetuned_v2`, `flat_classes=276`
- **yono-classify confirmed working**: end-to-end test returned `make=british, conf=0.57, ms=313ms, available=true, source=yono`
- **YONO_SIDECAR_URL in Supabase**: explicitly set to `https://sss97133--yono-serve-fastapi-app.modal.run` (confirmed)
- **Fixed**: `yono/scripts/upload_tier2_to_modal.sh` had `sss73133` typo → corrected to `sss97133`
- **Note**: `modal deploy` CLI output shows wrong URL (`sss73133`) — display bug, actual workspace slug is `sss97133`

### [vp-extraction] Import queue backlog investigation — 2026-02-27
- Alert fired: extractable count hit 1,000 (threshold 500)
- Investigation confirmed: NOT stalled. 100+ active workers, 1,305 items/hr, 0 stale locks
- Failures: 59 total, all quality gate rejections (missing year/make/model) — expected behavior
- Extractable breakdown: Other 638, Cars & Bids 360, BaT 2
- ETA to clear: ~48min — self-resolving demand spike, no action taken

### [cpo] SDK v1.3.0 — YONO Vision shipped — 2026-02-27
- **Release scope**: `nuke.vision.classify()`, `nuke.vision.analyze()`, `nuke.vision.batch()` — all live
- **`family` field added**: `api-v1-vision` now passes through `family` + `family_confidence` from YONO's tier-2 hierarchical classifier on all 3 routes (classify/analyze/batch)
- **SDK types updated**: `VisionClassifyResult` and `VisionAnalyzeResult` now include `family`, `family_confidence`, `is_vehicle`
- **`CHANGELOG.md` created**: `tools/nuke-sdk/CHANGELOG.md` with full v1.3.0 + v1.3.1 entries, historical v1.0–1.2 entries
- **OpenAPI spec updated**: `docs/api/openapi.yaml` — Vision tag added, `/api-v1-vision/classify`, `/analyze`, `/batch` endpoints fully documented
- **Work order filed**: `agent_tasks` id `00c0e808-ce31-4474-8032-73837903126a` — SDK v1.4.0: `nuke.signal.score()` market signal scoring (priority 85)
- **Next feature decision**: Signal score over comps — "Is this a good deal?" is the monetization unlock; comps is second

## 2026-02-26

### [cfo] Image Pipeline Unpause Cost Model — 2026-02-26
- Built full decision matrix: YONO-first hybrid strategy vs. full cloud vs. stay paused
- Key finding: $64K figure was wrong. Current Gemini-Flash pipeline = $0.0001/image (20x cheaper)
- Actual backfill cost: $3,250 (capped at $50/day × 65 days) for 32M images
- YONO covers: make/family classification (yono-classify, $0) + zone/condition/damage (yono-vision-worker, already running, not paused)
- Cloud still needed for: camera geometry, subject taxonomy, description, VIN/SPID detection
- Recommended threshold: 70% confidence (35-40% cloud escalation rate)
- Monthly ongoing: $130-180/month vs $2,000/month cloud-only
- Full model: `.claude/CFO_IMAGE_PIPELINE_COST_MODEL.md`
- Email recommendation sent to CEO

### [worker] RLS Audit — vehicles, vehicle_observations, auction_comments — 2026-02-26
- **vehicle_observations**: RLS was completely disabled — enabled it + added `vo_service_role_all` (ALL for service_role) and `vo_authenticated_read` (SELECT for authenticated users on public/owned vehicles)
- **vehicles.allow_vehicle_inserts**: dropped — it was `{public}` role with `WITH CHECK = true` (anon inserts). Replaced with `vehicles_authenticated_insert` scoped to `{authenticated}` + `auth.uid() IS NOT NULL`
- **vehicles.vehicles_delete_policy**: changed from `{public}` to `{authenticated}` role
- **auction_comments**: already secure — no changes needed
- Migration: `supabase/migrations/20260226240000_rls_audit_core_tables.sql` applied directly to DB

## 2026-02-27

### [cto] Architecture Review: Modal Sidecar + Agent Infrastructure — 2026-02-27

**MODAL SIDECAR (yono/modal_serve.py):**
- `@modal.asgi_app()` + FastAPI: APPROVED — correct long-term pattern for multi-endpoint model serving
- `min_containers=1` at $0.06/hr idle: APPROVED — cold start is 10-15s (Florence-2), keepwarm justified
- Model storage split: Florence-2 in image (fast cold start), ONNX in volume (hot-swap on training updates) — APPROVED
- CONCERN #1 (Medium): No auth on Modal endpoint — raw URL is unauthenticated. Work order issued to VP AI: add bearer token middleware before SDK v1.3.0 launch.
- CONCERN #2 (Low): `/analyze/batch` runs up to 20 Florence-2 inferences via `asyncio.gather` — no semaphore. Single CPU core will serialize them anyway, but add `asyncio.Semaphore(5)` before high-volume pipeline use.

**AGENT INFRASTRUCTURE (.claude/agents/ + ralph-spawn.mjs + agent-monitor):**
- Atomic claim state machine (pending → claimed → in_progress → completed): APPROVED
- File-based persona system (CLAUDE.md per role): APPROVED — version-controlled, diffable, zero DB overhead
- ralph-spawn.mjs concurrency pool: APPROVED — correct pull-from-queue pattern
- agent-monitor deduplication (line 156: checks existing pending before insert): APPROVED — no flood risk
- CONCERN #3 (HIGH): No per-agent token budget. 100 turns × Sonnet pricing = up to $20/agent on complex tasks. With 22+ pending tasks at concurrency 5, single run could hit $100-400. Work order issued to CFO + VP Platform.
- CONCERN #4 (Medium): Unregistered agent types in queue — "sentinel", "guardian", "curator", "harvester", "oracle" have no personas in `.claude/agents/`. Ralph-spawn falls back to worker persona. May be intentional (worker-class agents), but no persona = no domain knowledge injection.
- CONCERN #5 (Low): DONE.md and ACTIVE_AGENTS.md have concurrent write race with >1 agent. Acceptable now. If concurrency >5, move state tracking fully to agent_tasks table.

**Work Orders Issued:** VP AI (auth middleware), CFO+VP Platform (token budget), VP AI (semaphore for batch analyze)

### [worker] vehicle_observations compound indexes — 2026-02-27
- EXPLAIN ANALYZE confirmed vehicle timeline query scanning 369K rows, taking 9.8s
- Created `idx_observations_vehicle_time`: `(vehicle_id, observed_at DESC) WHERE vehicle_id IS NOT NULL`
- Created `idx_observations_kind_time`: `(kind, ingested_at DESC)`
- Both CONCURRENTLY (no table lock). Table columns: `kind` (not observation_type), `ingested_at` (not created_at)
- Vehicle timeline query now uses compound index directly (no sort, no filter scan)



### [vp-platform] Admin panel overhaul — 2026-02-27
- `AdminHome.tsx`: Ralph Brief auto-loads snapshot on mount (no button click needed)
- `AdminHome.tsx`: Operational pulse block shows import_queue pending/failed, agent_tasks pending by type, agent inbox unread — live, refreshes every 30s
- `AdminHome.tsx`: Cards show live pending/unread counts with red alert borders when non-zero
- `AdminShell.tsx`: Nav badges on Inbox, Agent Inbox, Reviews, Verifications, Ownership Verifications — red count chips, refresh every 60s
- New page `AdminAgentInbox.tsx` at `/admin/agent-inbox` — reads agent_messages from Supabase, role filters (to/from), unread toggle, thread view, mark-read via agent-email edge function
- Routes + nav wired for `/admin/agent-inbox`



### [cto] ralph-spawn: Multi-Agent Parallel Task Executor — 2026-02-27
- Built `scripts/ralph-spawn.mjs` — orchestrates parallel Claude Code sessions against `agent_tasks` queue
- Uses `@anthropic-ai/claude-agent-sdk` `query()` function (no TTY issues, native async iteration)
- Atomic task claiming: `status='pending'` → `claimed` → `in_progress` → `completed/failed` prevents double-execution
- Concurrency pool: up to N workers (default 5) pull from queue, claim tasks, spawn agents, drain
- Persona loading: reads `.claude/agents/{role}/CLAUDE.md` as system prompt `append`; falls back to `worker` persona
- Options: `permissionMode: 'bypassPermissions'`, `settingSources: ['project', 'user']`, `maxTurns: 100`
- CLI flags: `--concurrency N`, `--agent <type>`, `--dry-run`, `--list`, `--max-tasks N`, `--model <name>`
- 22 pending tasks in queue ready to execute
- Run: `dotenvx run -- node scripts/ralph-spawn.mjs --concurrency 5`
- Committed: `6ed85a0e9`



### [vp-ai] YONO Post-Sidecar Brief + Tier-2 Upload Script — 2026-02-27
- Assessed live training state: zone classifier PID 12814 (epoch 8/15), tier-2 watcher PID 39959 standing by
- PID 34496 confirmed complete (hier_american_best.pt + hier_family_best.pt in outputs/hierarchical/)
- Built `yono/scripts/upload_tier2_to_modal.sh`: polls for "=== DONE ===" in tier2_remaining.log, uploads all hier_*.onnx + hier_labels.json to Modal volume yono-data /models/, prompts redeploy
- Filed work order fdf5038f-7eb5-40ab-9b3b-3154f9da175a (vp-ai, priority 85) for upload execution ~5-6h from now
- Image pipeline unpause deferred: requires CFO cost model coordination + CEO approval (tier-2 + zone must complete first)

### [coo] All-hands CEO Briefing — 2026-02-26
- Executed startup sequence: inbox, queue health, PID verification, cron status
- Identified 3 status corrections vs CEO brief: quality backfill (237-240) paused not running; PID 34496 done (zone classifier 12814 + watcher 39959 continuing); geocode PID changed 8523→54824
- Created 5 new all-hands tasks: vp-deal-flow, vp-orgs, vp-photos, vp-docs, vp-vehicle-intel
- Dispatched work orders to all 14 cabinet members via agent email system
- Sent CEO real email brief with corrections and open questions
- Import queue state: 105K pending, 341 processing (mecum 51.8K, C&B 29.2K, B-J 18.4K)

### [infra] pgBouncer Connection Pooling — Transaction Mode
- **Secret set**: `NUKE_DB_POOL_URL` = `postgresql://postgres.qkgaybvrernstplzjaam:[password]@aws-0-us-west-1.pooler.supabase.com:6543/postgres` (pgBouncer transaction mode)
- **Note**: `SUPABASE_DB_URL` prefix is now blocked by Supabase CLI/API, so pooler URL uses `NUKE_DB_POOL_URL`
- **4 edge functions updated** to prefer `NUKE_DB_POOL_URL || SUPABASE_DB_URL`:
  - `agent-email` — added `prepare: false` to postgres.js client (required for transaction mode; postgres.js prepares by default)
  - `db-stats` — 3 connection sites updated
  - `investor-portal-stats` — updated
  - `map-vehicles` — updated
- **All 4 deployed** via `supabase functions deploy`
- deno-postgres `Pool` (used by db-stats, investor-portal-stats, map-vehicles) does not use prepared statements with template literals — transaction mode compatible without changes



### [docs] Document OCR Pipeline — Storage Bug + Re-extraction + Cron Setup
- **Storage bug fixed**: `getImageAsBase64` in `document-ocr-worker` was hardcoding `deal-documents` bucket for all signed URLs. Items with full `vehicle-images` HTTPS URLs now try direct fetch first, fallback to signed URL via regex-parsed bucket name.
- **RLS fixed**: `document_ocr_queue` had RLS enabled with no policies. New-style `sb_secret_...` key doesn't bypass RLS through PostgREST. Applied `allow_all` universal policy — function now sees all 916 rows.
- **Ollama backfill**: discovered ALL 486 "complete" items were extracted by ollama (llama3.2-vision:11b) which returned empty data. Re-queued 384 poorly-extracted items (null vin AND null make) back to `pending` with higher priority (10 for vehicle-ID docs, 5 for others).
- **Cron added**: `document-ocr-worker-batch` — runs every 5min, batch_size=3, processes pending items with Claude Sonnet.
- **Stale lock cleanup cron**: `document-ocr-stale-lock-cleanup` — runs every 3min, resets items stuck in classifying/extracting/linking for >5min back to pending.
- **Verified**: Claude Sonnet now being used (`extraction_provider: "anthropic"`), vehicle linking working (cost_sheet linked to vehicle_id).
- **Queue status**: ~280 pending, 105 complete, 529 skipped, processing at ~3 items/5min.



### [deal-flow] Transfer System — Cross-Department Architecture + Notifications
- **Audit**: found ownership_transfers (30K rows), all stalled at step 1, zero vehicle_transactions rows, no party notification
- **Migrations applied**:
  - `add_ownership_transfer_tokens` — buyer_access_token + seller_access_token on ownership_transfers (unique indexed, auto-populated all 30K rows)
  - `link_vehicle_transactions_to_ownership_transfers` — ownership_transfer_id FK on vehicle_transactions
- **Brief**: `.claude/VP_DEAL_FLOW_TRANSFER_BRIEF.md` — full cross-department coordination doc with CTO/CFO/CPO/VP Platform decisions
- **`notify-transfer-parties`** deployed — outbound SMS (Twilio) + email (Resend) for seeded/milestone_advanced/stalled/overdue; fire-and-forget, never blocks
- **`transfer-automator`** updated — calls notify-transfer-parties after both seedFromAuction and seedFromListing
- **Note**: Twilio 401 — env creds need setting in Supabase secrets; Resend email confirmed working
- **Remaining**: stripe-checkout-transfer function + payment_confirmed milestone wiring (VP Deal Flow)
- **VP Platform tasks**: /admin/transfers dashboard, /t/:token buyer-seller page, Log a Deal modal (see brief)

### YONO Modal Sidecar — Florence-2 Vision Deployed 2026-02-27
- Updated `yono/modal_serve.py`: added `/analyze` and `/analyze/batch` endpoints
  - Uses fine-tuned Florence-2 VehicleVisionHead (`finetuned_v2` mode)
  - Returns: vehicle_zone, zone_confidence, condition_score, damage_flags, modification_flags, interior_quality, photo_quality
  - Photo_type → zone mapping (ext_front, ext_rear, ext_driver_side, int_dashboard, mech_engine_bay, etc.)
  - Zero-shot fallback for when fine-tuned head fails to load
- Uploaded to Modal volume (yono-data): `yono_vision_v2_head.safetensors`, `yono_vision_v2_config.json`, `hier_family.onnx.data`
- Florence-2-base pre-baked into Modal image (`_download_florence2` run_function)
- URL: `https://sss97133--yono-serve-fastapi-app.modal.run`
- Set `YONO_SIDECAR_URL` in Supabase secrets and local .env
- Validated: yono-classify (ms=40), yono-analyze (mode=finetuned_v2, ms=9-10s on CPU)
- Old warm container draining naturally (within 10min of inactivity)

## 2026-02-26 (Rally RD competitor import)

### Rally RD Fractional Ownership Cars — IMPORTED 2026-02-26
- Created `scrape_sources` entry for Rally Rd. (id: 36a0b276-0710-4472-a886-869a807ea090)
  - url: https://www.rallyrd.com, source_type: marketplace, pattern: `rallyrd\.com`
  - `scrape_config` tags it as `fractional_ownership` competitor
- `observation_sources` already had rally-rd entry (id: ac3abc03-bf47-4fd1-8812-f26a293350f2)
- Inserted 9 vehicles into `import_queue` (all status=pending, source_id auto-linked, priority=10)
  - `raw_data` carries: platform, competitor:true, fractional_ownership:true, market_cap, share_price, provenance, mileage
  - 1955 Porsche 356 Speedster, 1965 Ford Mustang Fastback ($110K market cap), 1977 Lotus Esprit S1 (James Bond)
  - 1978 Aston Martin V8 Vantage Oscar India (URL had false-positive 'art' filter, manually overridden)
  - 1985 Ferrari Testarossa (Don Johnson/MJ/Elton John/Dr. Dre), 1988 Lamborghini Jalpa (Rocky IV)
  - 1994 BMW 850CSi (1 of 225 NA), 2003 Saleen S7 ($420K market cap), 2005 Ford GT (371 miles)
- No pre-existing rallyrd.com data found in DB
- No `competitor_platforms` table exists; data stored via standard scrape_sources + import_queue

## 2026-02-26 (YONO sidecar + agent infrastructure session)

### YONO FastAPI Sidecar — SHIPPED TO MODAL — COMPLETED 2026-02-26
- `yono/modal_serve.py` rewritten to use `@modal.asgi_app()` — single base URL with path routing
- Deployed: `https://sss97133--yono-serve-fastapi-app.modal.run`
- Fixed: onnxruntime 1.17.3→1.19.2 + `numpy<2` (NumPy 2.x incompatibility), `allow_concurrent_inputs`→`@modal.concurrent` deprecation
- `YONO_SIDECAR_URL` set in Supabase secrets
- Full round-trip validated: `yono-classify` → Modal → ONNX → `{"make":"german","confidence":0.78,...,"available":true}`
- Endpoints: GET /health, POST /classify, POST /classify/batch
- `min_containers=1` keeps one warm (avoids cold starts)
- P85 + P100 agent_tasks both marked completed

### Multi-Agent Infrastructure — COMPLETED 2026-02-26
- `CODEBASE_MAP.md` — 413-line semantic map of all 397 edge functions (27KB)
- `NUKE_COMPANY_BRIEF.md` — constitutional document loaded by all agents
- `.claude/agents/` — CLAUDE.md files for all roles: coo, cto, cfo, cpo, cdo, vp-extraction, vp-ai, vp-platform, vp-vehicle-intel, vp-deal-flow, vp-orgs, vp-docs, vp-photos, worker
- `~/bin/open-agent` — launches any role with session resume support
- `~/bin/save-session` — persists session ID for future resume
- `~/bin/list-tasks` — shows pending agent_tasks queue
- `agent-monitor` edge function — reactive issue scanner, pg_cron job 235 every 5min
  - Detects: stale locks, import queue backlog, BaT tasks stuck, missing quality scores, YONO down
  - Creates agent_tasks routed to correct VP automatically

## 2026-02-26 (YONO vision v2 session)

### YONO Vision V2 — Zone System + Auto-Launcher — COMPLETED 2026-02-26

**Zone labeling:** 100% complete. All 2764 records in `training_labels/labels.jsonl` now have `vehicle_zone` from the 41-zone taxonomy. Zone distribution: ext_front_driver=260, int_dashboard=222, mech_engine_bay=219, ext_driver_side=216, other=206, ext_undercarriage=197...

**Zone classifier training:** Watcher launched (PID 80532). Polls until condition model (PID 68092) finishes, then auto-launches `train_zone_classifier.py --epochs 15`. Logs to `yono/outputs/zone_classifier/watcher.log` and `training.log`.

**Bug fixed:** `_zone_classifier` missing from `global` declaration in `server.py` lifespan function — would have caused ZoneClassifier to always be None at module level even after loading.

**Scripts:**
- `yono/scripts/wait_then_train_zones.sh` — watcher that auto-launches zone training after condition model finishes
- `yono/outputs/zone_classifier/` — output directory created

**Background processes:**
- PID 68092: `train_florence2.py` — epoch 3/10, still running. Watcher waiting on this.
- PID 80532: `wait_then_train_zones.sh` — watching PID 68092, will auto-launch zone training.

**What to do after both finish:**
1. Restart `server.py` to load both fine-tuned models
2. Run `generate_condition_report.py --all-bat` to build condition reports
3. Install colmap (`brew install colmap`) then run `bat_reconstruct.py`

### YONO Vision V2 — Phase 1-4 Infrastructure — COMPLETED 2026-02-26

**What was killed:** EfficientNet-B0 make/model classifier as the primary direction. Make/model is already known from text. Vision should answer what text cannot.

**New architecture:** Florence-2-base (microsoft/florence-2-base, 231M params) with multi-task classification head for:
- `condition_score` (1-5): exterior condition
- `damage_flags` (multi-label): rust, dent, crack, paint_fade, broken_glass, missing_parts, accident_damage
- `modification_flags` (multi-label): lift_kit, lowered, aftermarket_wheels, roll_cage, engine_swap, body_kit, exhaust_mod, suspension_mod
- `photo_quality_score` (1-5): photo usefulness filter
- `interior_quality` (1-5 or null): interior condition when visible
- `photo_type` (9 classes): exterior_front/rear/side, interior, engine, wheel, detail, undercarriage, other

**Phase 1 — Auto-labeling:**
- [built] `yono/scripts/auto_label_images.py` — samples 3000 images from .image_cache/, sends to claude-haiku-4-5-20251001 vision, writes to training_labels/labels.jsonl
- [running] Labeling PID 62327: ~2500+ labels generated, 4 workers, finishing ~3000 total
- [data] Labels at `yono/training_labels/labels.jsonl` — 2488+ rows
- [data] Distribution: 40% score-4 condition, 38% have damage, 20% have mods, diverse photo types

**Phase 2 — Florence-2 fine-tuning:**
- [built] `yono/scripts/train_florence2.py` — full fine-tuning script for MPS/Florence-2
- [fixed] Florence-2 processor compatibility: pinned transformers==4.49.0, installed einops
- [running] Training PID 68092: epoch 1/10 in progress on MPS, loss dropping from 7.87→7.0
- [arch] DaViT vision encoder (4 block groups), `model._encode_image()` → (batch, 577, 768) features
- [arch] VehicleVisionHead: mean-pool over 577 tokens → LayerNorm → 512 → 6 task heads
- Checkpoints save to `yono/outputs/florence2/`, best model to `yono/models/yono_vision_v2_head.safetensors`

**Phase 3 — Server update:**
- [deployed] `yono/server.py` updated with `VisionAnalyzer` class and new endpoints:
  - `POST /analyze` — single image → condition_score, damage_flags, modification_flags, photo_quality, photo_type
  - `POST /analyze/batch` — up to 20 images
  - Existing `/classify` endpoint UNCHANGED (production-safe)
- [arch] VisionAnalyzer auto-detects: if `yono_vision_v2_head.safetensors` exists → fine-tuned mode, else → zero-shot captioning mode
- [note] Zero-shot Florence-2 generates `<DETAILED_CAPTION>` text, extracts flags via keyword matching

**Phase 4 — Edge function + DB:**
- [deployed] `supabase/functions/yono-analyze/index.ts` — deployed to Supabase
  - Single image: `{ image_url, image_id? }` → analysis result + optional DB write
  - Batch: `{ images: [{ image_url, image_id? }] }` → batch results
  - Auto-writes to vehicle_images when image_id provided
- [deployed] DB migration `database/migrations/20260226_yono_vision_v2.sql` applied:
  - Added to vehicle_images: condition_score, damage_flags, modification_flags, photo_quality_score, vision_analyzed_at, vision_model_version
  - All 6 columns verified present in production DB
  - Indexes: idx_vehicle_images_condition_score, idx_vehicle_images_damage_flags (GIN), idx_vehicle_images_pending_vision

**What still needs to complete (background processes running):**
- Labeling (PID 62327): ~500 more to finish → 3000 total
- Training (PID 68092): epoch 1/10 running, ~55 min total
- After training: `yono/models/yono_vision_v2_head.safetensors` auto-saved, server restarts load it

## 2026-02-26 (vehicle-profile session)

### Vehicle Profile Page — Finished — COMPLETED 2026-02-26
- [facts] data_quality_score (0-100 integer) now shows in VehicleBasicInfo with color-coded progress bar
- [facts] FactExplorerPanel (was defined but never rendered) now shows in Facts tab
- [evidence] WorkMemorySection (was imported but never rendered) now shows for owners/contributors in Evidence tab
- [commerce] Fixed double-wrapping: VehicleROISummaryCard + VehiclePricingValueCard both have internal CollapsibleWidgets; removed outer wrappers that were hiding content
- [commerce] VehicleDealJacketForensicsCard: replaced null return with "No deal jacket forensics available" empty state
- [header] Area Demographics: replaced confusing -- dashes with clean "unavailable" state
- [sanitizer] VehicleBasicInfo: reject mid-sentence fragments (", and four-wheel disc brakes" type contamination)
- All 4 tabs verified crash-free on both minimal-data and rich-data vehicles
- Committed 5a915f327, pushed, Vercel deploying

## 2026-02-26 (evening session continued)

### Order Book Matching Engine + market_fund_buy Cash Fix — COMPLETED 2026-02-26
- deduct_reserved_cash(), credit_cash(), release_reserved_cash() — cash settlement helpers
- market_fund_buy() rewritten: atomic cash deduction before share issuance (was TODO/skipped)
- match_order_book(order_id): full price-time priority matching engine
  - Price-time priority (best price first, oldest order first)
  - Fill at maker price, 2% commission deducted from seller proceeds
  - share_holdings ON CONFLICT upsert for buyer, decrement for seller
  - Cash settlement via helper functions; over-reserved cash released on full buy fill
  - FOR UPDATE SKIP LOCKED for concurrent safety
  - Updates market_orders, share_holdings, vehicle_offerings in one transaction
- cancel_market_order(): SECURITY DEFINER cancel + releases reserved cash (unfilled portion)
- tradingService.ts cancelOrder(): now calls cancel_market_order RPC (was direct table update, cash never released)
- Migration: 20260226_order_book_and_fund_buy.sql — committed 6028c0377, pushed

## 2026-02-26 (afternoon/evening session)

### Queue Throughput — 6 new source workers added
- Mecum: 3 new CQP workers (jobs 217-219), `* * * * *` continuous
- PCarMarket: 3 new CQP workers (jobs 220-222), `* * * * *` continuous
- 21,028 Mecum + 5,578 PCarMarket now actively draining

### Failed Record Triage — 0 failed remaining
- BaT: Skipped category pages + template URLs (Invalid BaT URL errors)
- BaT: Reset 1 transient 406 error
- BroadArrow: Skipped memorabilia (watches, scale models, sold page)
- BroadArrow: Reset legitimate vehicle failures (wrecker/fire truck)
- BJ: Reset invalid-routing failures (were hitting wrong extractor)
- Duplicate VIN: Skipped gracefully

### Quality Score Backfill — Fixed + Running
- **Root cause found**: 47 triggers × 89 indexes = 710ms/row
- **Fix 1**: Dropped `idx_vehicles_quality_score` and `idx_vehicles_quality_backfill` (no longer needed during backfill)
- **Fix 2**: DO block with `SET LOCAL session_replication_role = 'replica'` bypasses all 47 triggers → 20ms/row
- **Fix 3**: Temp table JOIN pattern (`_qb_batch`) for efficient query planning instead of `ANY(array)`
- **Fix 4**: 30-second sleep offset to stagger from peak cron contention at :00
- Cron 228: `quality-score-backfill`, 300 rows/run at :30 past each minute
- `quality_backfill_state` table tracks keyset pagination cursor (last_vehicle_id)
- Rate: ~300 rows/min = 18k/hr → ~69 hours for 1.25M records
- `trg_update_vehicle_quality_score` trigger fixed (×100 multiplier, was truncating to 0)

### YONO Export Script — ctid Pagination Fix — COMPLETED 2026-02-26

- Root cause: planner uses PK index → scans 28M rows → Supabase 120s timeout; partial index has reltuples=0 (ignored)
- Fix: rewrote `export_supabase_training.py` to use **ctid-based physical page range scans** (8000 blocks/batch = ~2300 rows, ~6s per batch)
- Added `--skip-download` flag: exports all JSONL metadata without downloading images (saves disk space — only 33GB free)
- New ctid batches start at batch_0103+ (existing 100+2 batches preserved)
- Export running: ~838K records, ETA ~1hr, writing to `training-data/images/`
- Also built `idx_vi_training_covering` covering index (usable once planner stats update via future VACUUM)

### Market Exchange Backend — COMPLETED 2026-02-26

- `pre_trade_risk_check` RPC deployed (was missing — orders fell open)
- `update_vehicle_offering_prices()`: share price = nuke_estimate / total_shares, >0.5% threshold
- `mark_to_market()`: updates unrealized P&L on share_holdings + market_fund_holdings
- `market_segment_stats_cache` table: pre-computed stats, avoids 2-min full table scan
- `refresh_segment_stats_cache()` + pg_cron job 212 (every 4h)
- `update_market_nav()`: reads cache, NAV = $10 × (current_cap / baseline_cap)
- `run_exchange_pricing_cycle()`: chains all steps, returns JSONB summary
- `update-exchange-prices` edge fn: cron-triggered, full cycle <1s
- `api-v1-exchange` edge fn: unified read API (funds+stats, offerings, holdings)
- Baselines: PORS $5B, TRUK $1.25B, SQBD $80M, Y79 $317M. All funds at NAV $10.00.
- MarketExchange.tsx + MarketFundDetail.tsx: replaced slow RPC with api-v1-exchange (instant load)
- pg_cron job 213: pricing cycle every 15min

### EXIF Pipeline Forward-Fix + Image Bundle Review UX — COMPLETED 2026-02-26

**What was built (continuation of EXIF backfill session):**

**Daemon EXIF format fix (`scripts/photo-auto-sync-daemon.py`):**
- Fixed `create_vehicle_image_record()` to write structured EXIF format instead of flat: `{camera: {make, model}, location: {latitude, longitude}, DateTimeOriginal, exif_status: 'synced_from_photos'}`
- Previously wrote flat `{camera_make, camera_model}` which bypassed `reprocess-image-exif` filter checks
- Now future photo syncs produce EXIF data that matches the system's expected schema

**Image Bundle Review UX (all pieces now wired):**
- `BundleReviewQueue.tsx` — fully built component (review queue card in Evidence tab)
- `auto-create-bundle-events` edge function — deployed, creates `timeline_events` with `needs_input: true` per bundle
- `suggest-bundle-label` edge function — deployed, uses Claude Vision to suggest event title/type
- Gallery `bundles` view mode — "Sessions" toggle already in ImageGallery.tsx
- `VehicleProfile.tsx` — added fire-and-forget call to `auto-create-bundle-events` on owner profile load

**Dave's GMC K2500 current state:**
- 4 events with `needs_input: true`: Sep 25, Oct 01, Oct 18, Feb 10
- All 4 have AI suggestions pre-baked in `metadata.ai_suggestion`
- All 580 images have correct `taken_at` (clean 5-session timeline)
- BundleReviewQueue renders these automatically in the Evidence tab

**Commit:** 76a35a4d7, pushed to main, Vercel deploying

### data_quality_score Backfill — COMPLETED 2026-02-26

**What was built:**
- Fixed `trg_update_vehicle_quality_score` trigger: was storing raw 0.0-1.0 decimal into INTEGER column (all truncated to 0). Now stores `ROUND(compute_vehicle_quality_score(NEW) * 100)::INTEGER` (0-100 scale).
- Backfilled ~6,517 records manually in 300-500 row batches via psql (pooler timeout ~2min enforced; 300 rows ~safe).
- Cron job `quality-score-backfill` (job 211) confirmed active: runs every minute via `quick_quality_backfill(500)` function — auto-completes remaining ~1.247M records at ~500/min = ~720K/day, done in ~40hrs.

**Grade distribution of first 6,517 scored records:**
- A (80-100): 2,546 (38.8%) — year + make + model + extras
- B (60-79): 3,224 (49.1%) — year + make + model, some extras
- C (40-59): 292 (4.4%) — partial identity fields
- D (20-39): 45 (0.7%) — minimal data
- F (0-19): 456 (6.9%) — mostly deleted/stub records

### Location Pipeline Fix + Geocode Backfill — COMPLETED 2026-02-26

**What was built:**
- `_shared/parseLocation.ts` — new shared utility that parses "City, ST 12345" / "City, State ZipCode" strings into `{city, state, zip, clean, raw, confidence}`. Wraps normalizeListingLocation, strips zip before regex check to avoid false rejections.
- `extract-bat-core`: now uses `parseLocation()`, writes `listing_location_raw/source/confidence/observed_at` on insert + update. Writes row to `vehicle_location_observations` after each extraction.
- `extract-cars-and-bids-core`: fixed `location:` → `listing_location:` (was writing to wrong column). Added all `listing_location_*` fields. Writes `vehicle_location_observations`.
- `process-cl-queue`: upgraded `normalizeListingLocation` → `parseLocation`. Added `vehicle_location_observations` write on insert + update paths.
- `geocode-vehicle-locations` edge function: batch geocoder for backfill. Uses `fb_marketplace_locations` lookup first (instant), Nominatim fallback (1 req/sec). Returns `{processed, geocoded_from_lookup, geocoded_from_nominatim, failed}`.
- `scripts/geocode-backfill.mjs`: local Node.js script for overnight backfill of 28k existing vehicles. Running as background process (PID 92797, log: /tmp/geocode-backfill.log).

**Schema used (no migrations needed — all columns already exist):**
- `vehicles.listing_location`, `listing_location_raw`, `listing_location_source`, `listing_location_confidence`, `listing_location_observed_at` — now populated by BAT, C&B, CL extractors
- `vehicles.gps_latitude`, `vehicles.gps_longitude` — being filled by backfill script
- `vehicle_location_observations` — now written on every extraction with city/state/confidence

**Current state (updated 2026-02-26 ~18:50):**
- Actual scope: 132,915 vehicles need geocoding (111,697 have listing_location from BAT/CL history, 28,700 have legacy location col — more than initial 28k estimate)
- Backfill running: PID 8523, ~1,498 geocoded so far, ~131k remaining
- DB index created: `idx_vehicles_geocode_backfill` on vehicles(id) WHERE (listing_location/location NOT NULL) AND gps_latitude IS NULL — enables keyset pagination without full table scan
- In-memory geo cache added to script: avoids repeat Nominatim calls for same city/state (estimate ~3-5k unique city/state combos in 133k records). Cache warms over first ~100 batches, then subsequent batches are near-instant.
- ETA: overnight (~10-15 hours given Nominatim rate limit on first pass, then cache-accelerated)
- Monitor: `tail -f /tmp/geocode-backfill.log` (stdout is buffered — DB writes happen live, log flushes in batches)
- Verify: `SELECT COUNT(*) FROM vehicles WHERE gps_latitude IS NOT NULL;`

## 2026-02-26

### [transfers] Transfer status badge live in VehicleHeader
- `transfer-status-api` edge function: GET/POST returns sanitized transfer state (milestone, progress, parties)
- `VehicleHeader.tsx`: badge shows current milestone label, progress %, days stale (≥7), buyer @handle with ◇ if unclaimed
- Badge color: blue=in_progress, amber=stalled, green=completed
- Committed 6e346eba7, deployed, Vercel building

### [transfers] Ownership transfer automation framework
- `transfer-automator`: seeds from auction_events close, ghost shell resolution, 28 milestones with deadlines
- `transfer-advance`: AI classifies email/SMS signals → advances milestones (Haiku + keyword fallback)
- `transfer-email-webhook`: Resend inbound → t-{10hex}@nuke.ag inbox routing
- `transfer-sms-webhook`: Twilio inbound → buyer/seller phone routing, TwiML ACK
- DB triggers: auction close → auto-create transfer; identity claim → upgrade ghost shell to real user
- Crons: staleness sweep every 4h (job 189); backfill 170k sold auctions in batches of 100 every 2min (job 190)
- 138 existing transfers backfilled with inbox_email

### [vision] api-v1-vision deployed + SDK v1.3.1 nuke.vision live on npm
- api-v1-vision edge function: POST /classify (YONO, $0), /analyze (YONO+cloud), /batch (100 images)
- tools/nuke-sdk/src/resources/vision.ts: nuke.vision.classify/analyze/batch — committed + published
- SDK v1.3.1 live at @nuke1/sdk on npm

### [context] Multi-agent coordination system built
- DONE.md + PROJECT_STATE.md + ACTIVE_AGENTS.md cleanup
- claude-checkpoint (Stop hook auto-saves git state) + claude-handoff (explicit agent handoff)
- Global CLAUDE.md: session start ritual + context pressure rule
- Dependabot: 3 high alerts resolved, gitignore fixed for tools/

### [bonhams] Import Queue Triage — 17,964 memorabilia pre-skipped
- Analyzed 24,037 pending bonhams records via URL pattern analysis
- Built vehicle indicator regex: chassis-no|frame-no|vin-|engine-no OR year-make slug patterns (~60 makes)
- `UPDATE import_queue SET status='skipped', error_message='memorabilia: skipped by url pattern'` — 17,964 records
- Remaining for extraction: 5,976 pending (5,042 bonhams.com + 934 cars.bonhams.com) — all genuine vehicles
- Scheduled 3 dedicated workers: `bonhams-queue-worker-1/2/3` (cron jobs 200/201/202), `* * * * *`, 5 lots/batch, 50s runtime
- Workers route through `continuous-queue-processor` → `extract-bonhams` (already configured in SOURCE_CONFIGS)

Format: `- [area] What was built — where it lives`

---

## 2026-02-26 (Extraction Quality Sprint — Phase 2, post context-compression)

### Critical Description Fix — Mecum
- **Root cause**: `post.content` in Mecum __NEXT_DATA__ is ALWAYS empty. Description lives in Gutenberg blocks under HIGHLIGHTS + EQUIPMENT headings.
- **Fix**: Added `parseBlocksDescription()` to extract-mecum — recursively walks `post.blocks[]`, finds `core/list-item` elements under HIGHLIGHTS and EQUIPMENT headings, strips HTML, joins with bullet format.
- **Also**: Engine extraction from SPECIFICATIONS block (label/value pairs in blocks, more reliable than `lotSeries` which is sometimes charity text).
- **Result**: Description rate from 0% → expected 60%+ for Mecum lots. Quality score example: 0.73 → 0.93.
- **Mecum backfill**: Reset 35,146 completed mecum items (processed before 2026-02-20) to 'pending' for re-extraction. 5 dedicated mecum CQP workers (jobs 217-219, 231-232) actively draining.

### Critical Description Fix — Bonhams
- **Root cause 1**: `extractBonhamsLot` only looked at `jsonLd.description` (generic site text) and meta description. The actual lot description is in `### Footnotes` section of the Firecrawl markdown.
- **Root cause 2**: JSON-LD/og:title not available in React shell HTML → year/make/model were null.
- **Root cause 3**: Firecrawl only triggered when `html.length < 5000`, but Bonhams CSR shell is 120KB.
- **Fix 1**: Added Footnotes markdown section parsing in `extractBonhamsLot()` — regex matches `### Footnotes\n+...`, strips markdown formatting, trims to 10K chars.
- **Fix 2**: Added markdown heading fallback for title parsing when og:title unavailable.
- **Fix 3**: Firecrawl now fires when `!fetchResult.cached && !hasLotContent` — fires on all fresh fetches (not just tiny pages). Cache hit = uses stored markdown, no Firecrawl cost.
- **Result**: Description rate from 0% → expected 60%+ for Bonhams lots. All tested at cost_cents=0 (cached). Fresh fetches use Firecrawl (~$0.01/page × 2.6K pending = ~$26).

### Queue Workers Added
- Jobs 231, 232: mecum-queue-worker-4, mecum-queue-worker-5 (5 total mecum CQP workers now)
- Jobs 233, 234: gooding-queue-worker-1, gooding-queue-worker-2 (Gooding was only in general round-robin, now dedicated)
- Jobs 229, 230: removed (bad re_enrich implementation that caused timeout)

### Pipeline State (current)
- Mecum: 55K pending / 731/hr → ~75 hrs | B-J: 24K / 2028/hr → ~12 hrs | C&B: 31K / 989/hr → ~31 hrs
- BaT: 4K / 844/hr → ~5 hrs | Bonhams: 2.6K / 671/hr → ~4 hrs | PCar: 5.1K / 164/hr → ~31 hrs | Gooding: 1.6K / (new workers, accelerating)

## 2026-02-26
- [cron] **9 dedicated source workers added** (jobs 191-199): cnb-queue-worker-1/2/3, bj-queue-worker-1/2/3, broadarrow-queue-worker-1/2/3 — each runs every minute, batch_size=5, continuous=true, max_runtime=50s. Targets C&B (36k pending), BJ (8.4k pending), Broad Arrow (1.1k pending). BAT already covered by jobs 123-127.
- [extraction] **14,616 stuck items rescued** — reset to pending: Barrett-Jackson (8,254), C&B (3,301), BaT (1,821), Broad Arrow (1,151), Vanguard/Hemmings/CC (89)
- [extraction] **extraction-watchdog**: added step 5b — rescues orphaned `status='failed'` items (claim function only picks pending; failed items were permanently abandoned by old PIQ code path)
- [extraction] Root causes documented: (1) claim fn ignores failed status, (2) watchdog ate items before 2/25 extractor rewrite, (3) bulk 2/17 importer had multi-word make parser bug (Aston Martin→make='Aston',model='Martin')
- [extraction] PCarMarket 16,712 skipped items NOT reset yet — uses Firecrawl per call, needs decision on cost vs data value
- [pipeline] Discovery→extraction gap fixed: listings no longer expire before extraction triggers
- [bat] Removed dead workflows, restored bat-dom-map-health-runner
- [fb-marketplace] refine-fb-listing: og: meta tags, bingbot HTML fetch, skip-null-overwrites logic

## 2026-02-25
- [agent-safety] **TOOLS.md** — canonical intent→edge function registry. Read before building anything.
- [agent-safety] **pipeline_registry** table — 63 entries: table.column → owning function + do_not_write_directly flag
- [agent-safety] Column comments — 86 comments on vehicles, vehicle_images, import_queue, bat_extraction_queue, document_ocr_queue, vehicle_observations
- [agent-safety] CHECK constraints — vehicles.status, auction_status, reserve_status; vehicle_images.ai_processing_status, optimization_status, organization_status
- [agent-safety] release_stale_locks() SQL function + queue_lock_health view + hourly cron (job 188)
- [agent-safety] Released 375 stuck records on deploy (367 vehicle_images stuck since Dec 2025, 7 bat_extraction_queue, 1 document_ocr_queue)
- [cars-and-bids] extract-cars-and-bids-core full rewrite: direct HTML parsing, cache-first markdown, all fields, sale_price fix
- [fb-marketplace] HTML fallback + longer inter-city delay; residential-IP scraper for vintage vehicles
- [seller-blocklist] Seller blocklist edge function — blocks scammers and disguised dealers
- [discovery] Craigslist: private-sellers-only filter (cto param), seller_type tagging
- [pipeline] QA sweep, image pipeline improvements, URL normalization, content-hash dedup, VIN cross-validation
- [frontend] Lazy-load modal components in VehicleHeader

## 2026-02-24
- [rebrand] Marque → Nuke complete across all user-facing strings + domain nuke.ag live
- [frontend] Vehicle profile layout restored: 16:9 hero, expanded timeline/description/comments
- [contact-inbox] Inbound email via Resend webhooks + admin inbox UI
- [frontend] Workspace tabs, VIN dedup, deal pipeline inputs
- [investor-page] /offering: dynamic investor deck powered by live Supabase data (no hardcoded stats)
- [frontend] AppLayout decomposed into focused header/nav/footer components
- [build] React 18 / react-three circular ESM dep resolved; recharts/d3 chunk fix

## 2026-02-19
- [acquisition-pipeline] Market proof page with honest economics (parts+labor), CL discovery, batch processing
- [pipeline-page] Redesigned to match app design system; RLS policies added
- [acquisitions] Acquisitions nav link + acquisition pipeline dashboard UI

## 2026-02-18
- [frontend] CursorHomepage.tsx refactor: 6,449 → ~2,000 lines (extracted 8 hooks/components)
- [frontend] Landing page for logged-out visitors (hero, features, CTAs)
- [frontend] Removed 10 half-built product routes: betting, trading, invest, social, vault, portfolio
- [frontend] Rebrand N-Zero → Marque → Nuke in git history

## 2026-02-17
- [normalizeVehicle] Shared vehicle normalization utility — wired into 9+ extractors, eliminates toLowerCase anti-pattern
- [frontend] Lazy-load route modules + organization routes (400KB → on-demand)
- [security] XSS fixes, OG tags, JSON-LD structured data, canonical URLs
- [accessibility] Skip nav, ARIA labels, contrast ratios
- [cleanup] Deleted 228 files / 74k lines of dead code (_archived dirs)
- [deps] Consolidated: icon libs → lucide-react only; EXIF libs → exifr only
- [db] Vehicle DB indexes + status column constraints

## 2026-02-15
- [bat-snapshot-parser] All-SQL BaT snapshot parser: 355k HTML snapshots, 6x throughput vs old version
- [photo-pipeline] Apple Vision pre-filter + Gemini orchestrator; skip junk URLs; skip analyze-image when no vehicle
- [frontend] Gallery view + advanced filters on collections map
- [frontend] Map: zoom/scope ring/concentration indicator, sidebar hover highlight, region tracking

## 2026-02-01 (multi-agent session — see .claude/AGENT_PRODUCTIVITY_LOG.md for full detail)
- [data-quality] Fixed 1,161 vehicles: invalid sale_price (reserve_not_met + price>0)
- [data-quality] Fixed 265 data inconsistencies (181 Class A, 77 B1, 7 B2). Verified 0 remaining.
- [bat] Price extraction bug fixed: scoped regex to essentials block only (was extracting quoted prices from user comments)
- [collecting-cars] **Typesense API bypass**: `https://dora.production.collecting.com/multi_search` — bypasses Cloudflare entirely, zero cost. Non-AI extractor built and deployed. 305 listings processed.
- [craigslist] extract-craigslist deployed: uses JSON-LD structured data, no AI needed
- [source-registry] source_registry table (13 sources) + views: v_active_sources, v_sources_needing_attention, v_ugly_sources
- [extraction-hierarchy] Full fallback stack deployed: Native → API Bypass → Firecrawl → Playwright → Ollama

## 2026-01-31
- [multi-agent] Multi-agent coordination system + ACTIVE_AGENTS.md convention established
- [schema-discovery] Schema Discovery principle formalized in CLAUDE.md
- [telegram] Telegram bot (@Sss37133_bot) + claude-notify hook + claude-log + check-in bot running
- [mecum] YouTube broadcast analysis pipeline + "Watch the Moment" (links vehicles to broadcast timestamps)
- [broadcast-backfill] Broadcast backfill queue system for agent processing
- [firecrawl-enrichment] Firecrawl enrichment (activates Feb 2) + cloud enrichment via GitHub Actions

## 2026-01-29
- [live-auctions] Live auction monitoring system (multi-platform sync)
- [copart-iaa] Copart/IAA HTML-in approach (Firecrawl dependency removed)
- [nhtsa] NHTSA integration added
- [orgs] OrgLogo component: auto-fetch from Clearbit/Google

## 2026-01-25
- [financial] Full financial products infrastructure (QuickBooks OAuth, webhooks, token exchange)
- [legal] NUKE LTD legal entity infrastructure — docs committed
- [market-intelligence] Market Intelligence Initiative: deployment guide + core components

## 2026-01-22-24
- [cars-and-bids] C&B comment extractor; enhanced extraction with auction image handling
- [ebay-motors] eBay Motors: VIN + mileage extraction
- [observations] **Vehicle observation system** (new architecture): observation_sources, vehicle_observations, observation_extractors, observation_discoveries tables
- [automated-bidding] Automated bidding system built

## 2026-01-23
- [bat-wayback] BaT Wayback Machine import with deduplication logic

## 2025-12-05-10
- [receipts] Comprehensive work order receipt system (ComprehensiveWorkOrderReceipt component + pipeline)
- [forensics] Forensic bundling: component lifecycle tracking, before/after detection, scan history
- [service-manuals] Service manual indexing pipeline (OpenAI/Anthropic, not Gemini)
- [catalog] 3M Automotive Aftermarket Catalog 2024 indexed
- [catalog] Material catalog & TDS indexing system
- [labor] Fluid labor rate system with parallel calculations
- [vins] VIN multi-proof system using existing tables
- [photo-pipeline] Part-number OCR, receipt-photo OCR, TechCapture page
- [orgs] Organization intelligence system + image auto-matching
- [knowledge-library] Knowledge Library implementation
- [vehicle-mailbox] Vehicle mailbox system (VehicleMailbox component + message management)
- [bundle-analysis] Bundle grouping and analysis system via Supabase edge function

## 2025-11-24-30
- [auth] Google OAuth login
- [api-access] API access payment system (users pay, use own keys)
- [bat-comments] BaT comment tracking: database schema, scheduled scraping, admin notifications
- [lightbox] Full-resolution lightbox + EXIF data panel (sidebar, all data sections)
- [about] Comprehensive About page (maps, ERDs, frameworks)
- [app-layout] Double-wrapping prevention system for AppLayout

## 2025-10-16-18
- [deployment] Vercel production deployment pipeline established; nuke.ag domain
- [mobile] Mobile camera capture with AI guardrails
- [rarity] Vehicle rarity system (Marti Reports style, production data)
- [cards] Card UI foundation: swipe, double-tap like, price widgets, readiness bar
- [streaming] Livestream system (viewer_user_id, get_live_streams_feed)

---

## How to Append

When you complete significant work, add a line at the TOP of the relevant date section:
```
- [area] Description of what was built — edge function name or file path if relevant
```

Start a new date section if today's date isn't already here.

### Ownership Transfer Automation Framework — COMPLETED 2026-02-26

**What was built:**
- `transfer-automator` edge function: seeds transfers from auction_events closes, handles idempotency, resolves/creates ghost shell identities, seeds 18-28 milestones with deadlines
- `transfer-advance` edge function: AI classifies free-form signals (SMS/email/platform events) against pending milestones, advances them, stores communication records; falls back to keyword heuristics when no AI key
- DB trigger `trg_auto_create_transfer_on_auction_close`: fires AFTER INSERT/UPDATE OF outcome on auction_events where NEW.outcome='sold', calls transfer-automator via pg_net async
- DB trigger `trg_upgrade_transfers_on_identity_claim`: fires when external_identities.claimed_by_user_id changes NULL→value, auto-populates to_user_id/from_user_id on matching transfers (ghost shell → real user upgrade)
- `transfer_staleness_sweep(stale_days)` SQL function: marks overdue milestones + stalled transfers, safe to call from cron or edge function
- Cron job 189 `transfer-staleness-sweep`: runs `transfer_staleness_sweep(14)` every 4h
- `backfill_transfers_for_sold_auctions(batch_size)`: backfill pg_net caller for existing 170k sold auctions

**Schema extended:**
- `transfer_communications` got: milestone_type_inferred, ai_classification_confidence, has_attachments, attachment_names, raw_metadata
- `communication_source` enum extended with 'document'

**Entry points:**
- New auction closes: automatic via DB trigger → pg_net → transfer-automator
- Email webhook: POST /transfer-advance {action: "ingest_email", transfer_id, from_email, subject, body_text}
- SMS webhook: POST /transfer-advance {action: "ingest_sms", transfer_id, from_number, body_text}
- Manual advance: POST /transfer-advance {action: "advance_manual", transfer_id, milestone_type}
- Query state: POST /transfer-automator {action: "get_transfer", vehicle_id or transfer_id}

### Transfer Webhook Integration — COMPLETED 2026-02-26

**New edge functions:**
- `transfer-email-webhook` — Resend inbound email webhook handler
- `transfer-sms-webhook` — Twilio inbound SMS webhook handler

**Schema additions:**
- `ownership_transfers`: inbox_email, buyer_phone, seller_phone, buyer_email, seller_email
- `transfer_status` enum: added 'stalled' value
- `transfer_communications`: milestone_type_inferred, ai_classification_confidence, has_attachments, attachment_names, raw_metadata

**Webhook URLs (live):**
- Email: https://qkgaybvrernstplzjaam.supabase.co/functions/v1/transfer-email-webhook
- SMS: https://qkgaybvrernstplzjaam.supabase.co/functions/v1/transfer-sms-webhook

**Routing logic:**
- Email: TO address `t-{10hex}@nuke.ag` → direct transfer lookup; FROM email → buyer_email/seller_email match
- SMS: FROM phone (10-digit normalized) → buyer_phone/seller_phone match

**Configuration needed:**
- Resend: Domain → nuke.ag → Inbound → catch-all `t-*@nuke.ag` → webhook URL above
- Twilio: Phone Number → Messaging → Webhook URL above, HTTP POST

**Per-transfer inbox:**
- Every transfer gets `inbox_email = t-{first10hexchars_of_trigger_id}@nuke.ag`
- 138 existing transfers backfilled with inbox_email
- Backfill buyer_phone/seller_phone via: POST /transfer-automator {action: "update_contacts", transfer_id, buyer_phone, buyer_email}

## 2026-02-26 (perf sprint)
- [perf] **SubdomainRouter**: compute initial state synchronously — eliminates "loading..." flash for non-storefront domains
- [perf] **useSession**: read Supabase session from localStorage cache synchronously — auth spinner eliminated for returning users; select('*') → explicit columns
- [perf] **vendor.js**: moved recharts + d3 out of vendor chunk into 'charts' chunk — vendor 813KB → 393KB (half)
- [perf] **useSession**: ref guard on fetchProfile — eliminates duplicate profiles query from getSession + INITIAL_SESSION double-fire
- [perf] **useNotificationBadge/useCashBalance**: user-scoped channel names (notification_badge:{userId}, balance:{userId})
- [perf] **VehicleProfile**: extracted readCachedSession() to utils/cachedSession.ts; initialize session + authChecked from cache — loadVehicle() no longer blocked on async getSession() round-trip

### YONO Hierarchical Inference — COMPLETED 2026-02-26
- `HierarchicalYONO` class added to `yono.py` — Tier 1 (8-family) + Tier 2 (per-family make) cascade with flat fallback
- `server.py` updated — lifespan handler, loads hierarchical model, /health reports tier1/tier2/flat state
- `models/hier_family.onnx` exported — 8-class family classifier (45.8% val_acc, epoch 19/25)
- `yono-classify` edge function updated — preserves inference path as `yono_source` field ("hierarchical"|"flat_fallback"|"flat")
- Tier 2 training running in background (american: 20 makes, 22.9K images; german/british/etc. queued)
- Supabase export resumed in background (100 batches done, resuming from offset 200K with 300s timeout fix)
- YONO server live on :8472 with hierarchical support

## 2026-02-26 (EXIF pipeline fix + image timeline)
- [data] **EXIF backfill**: Fixed chronological ordering for Dave's GMC K2500 (a90c008a) — 580 images now have correct taken_at
  - 62 images: updated via photo_sync_items.photos_date_taken (exact millisecond precision from Apple Photos sync)
  - 78 images: updated via local Photos library using osxphotos (real camera timestamps + GPS)
  - 250 images: BaT listing scrapes — taken_at updated from BaT CDN URL path (/uploads/2025/10/) → Oct 2025
  - All BaT images marked exif_status: 'stripped' (correct — BaT CDN strips user EXIF)
- [fix] **reprocess-image-exif edge function**: Fixed 2 crash bugs — null GPS dereference (structured.location.latitude), wrong column names (gps_latitude → latitude/longitude)
- [fix] **reprocess-image-exif**: BaT images with no EXIF now marked 'stripped' instead of silently failing
- [data] **Timeline integrity**: Oct 11 orphaned timeline_event_id fixed; images confirmed linked to 6 events
- [result] Final bundle state: Sep 25 (146), Oct 01 BaT listing (251), Oct 11 inspection (1), Oct 18 documentation (102), Feb 10 work session (78)

## 2026-02-26 (frontend perf: auth-gate waterfalls + bundle optimization)
- [perf] **Auth-gate waterfall elimination**: 17 pages total fixed — session state initialized from localStorage cache synchronously
  - VehicleProfile, Profile, CursorHomepage, Vehicles, Library, Capture, VehicleJobs, Capsule, CurationQueue, RestorationIntake, BusinessIntelligence, ImportDataPage (batch 1+2)
  - Dashboard, AdminMissionControl, AdminVerifications, SocialWorkspace, DeveloperDashboard, MarketDashboard, VaultPage, Portfolio, InvoiceManager, UnlinkedReceipts, PersonalPhotoLibrary (batch 3)
  - Added `nuke_frontend/src/utils/cachedSession.ts` — shared utility to read Supabase session from localStorage synchronously
- [perf] **Vendor bundle split**: recharts+d3 moved to separate 'charts' chunk — vendor.js reduced 813K → 393K
- [perf] **Double profile fetch eliminated**: useSession.ts useRef guard prevents INITIAL_SESSION + getSession() dual fetch
- [perf] **Lazy markdown loading**: InvestorOffering + OrganizationOfferingTab — 6 static `?raw` imports converted to dynamic per-tab imports (~378K now loaded on-demand)
- [fix] **User-scoped realtime channels**: notification_badge + cash balance channels now scoped by userId
- [fix] **SubdomainRouter synchronous init**: eliminated loading gate for non-storefront domains

## 2026-02-26 (extraction quality sprint — autonomous)

### PCarMarket 4-Layer Field Fix — DEPLOYED
- **Root cause**: PCarMarket extractor had no color/engine/transmission in interface, extraction path, LLM fallback, or vehicleData write — fields extracted by Firecrawl but never stored
- **Fix**: Added to all 4 layers — TypeScript interface, JSON extraction (`jsonData.vehicle?.exterior_color` etc.), LLM fallback (`llm.exterior_color` etc.), vehicleData write object (`color`, `interior_color`, `engine_type`, `transmission`)
- **Verified**: Porsche 993 test → "Zenith Blue Metallic", "Midnight Blue", "3.6 L flat-six, 282 HP", "6-Speed Manual" ✓
- **File**: `supabase/functions/import-pcarmarket-listing/index.ts`

### Backfill Queue — 88K+ items across all sources
All queued via `import_queue` → CQP → dedicated extractors. Free/low-cost extraction paths used where available.
- **Bonhams**: 24,978 shell records with NULL listing_source queued (old bulk importer predated extract-bonhams v3)
- **C&B**: 18,261 cab-fast-discover shells with no prior queue entry
- **Barrett-Jackson**: 13,602 B-J vehicles with no prior queue entry; 13,057 "complete" items reset where VIN was missing
- **BaT**: 8,052 BaT vehicles missing VIN or mileage re-queued
- **PCarMarket**: 5,483 existing PCarMarket vehicles missing color queued at low priority
- **Mecum**: 20,903 mecum-checkpoint/fast-discover shells with no prior queue entry (free __NEXT_DATA__ extraction)

### CQP Extractor Routing Fixes — DEPLOYED
- **Mecum**: Route changed `extract-vehicle-data-ai` → `extract-mecum` (dedicated, uses free `__NEXT_DATA__` JSON, quality gate, proper WordPress content extraction)
- **eBay**: Route changed `extract-vehicle-data-ai` → `extract-ebay-motors` (dedicated, quality filters, strict field validation)
- **File**: `supabase/functions/continuous-queue-processor/index.ts`

### v_extraction_quality View Created
```sql
-- Tracks field completeness by listing_source
-- Key fields: VIN, mileage, color, interior_color, engine, transmission, description, sale_price
SELECT * FROM v_extraction_quality ORDER BY pct_all_key_fields DESC;
```

### Pipeline Progress (snapshot ~4h after start)
- BaT: 696 complete, 7,957 pending
- B-J: 1,637 complete, 32,320 pending
- C&B: 773 complete, 34,943 pending
- Bonhams: 511 complete, 5,250 pending
- PCarMarket: active (5,563 pending)
- Mecum: 20,680 newly queued, extraction now routed to extract-mecum (free)

### Additional Extraction Quality Fixes (continued from session)

**CQP routing fixes** — `supabase/functions/continuous-queue-processor/index.ts`:
- `mecum` → `extract-mecum` (was `extract-vehicle-data-ai` — using free `__NEXT_DATA__` is 10x better quality)
- `ebay` → `extract-ebay-motors` (was `extract-vehicle-data-ai` — dedicated quality-filtered extractor)
- Gooding: added sourceIds for fast queue claiming (no more full-table LIKE scan)

**C&B snapshot cache fix** — `supabase/functions/extract-cars-and-bids-core/index.ts`:
- Removed 7-day TTL on listing_page_snapshots — historical auction pages are immutable once ended
- Old C&B data permanently lost from live pages; existing snapshots (19K) now reusable indefinitely

**Gooding backfill** — 1,724 old `gooding_extract` records (goodingco.com URLs) queued for `extract-gooding`:
- Were labeled 'gooding_extract' but had goodingco.com URLs — missed by B-J backfill
- extract-gooding getting rich provenance descriptions ("Brilliant George Weaver Design...", "Stunning One-Off Brewster/Inskip Coachwork")
- Quality improvement: 1.5% description → ~85% after extraction

**Pipeline throughput** (measured rates):
- B-J: 2,478/hr (25K pending, ETA ~10 hrs)
- C&B: 1,141/hr (32K pending, ETA ~28 hrs) 
- BaT: 1,022/hr (4.7K pending, ETA ~4.6 hrs)
- Bonhams: 741/hr (3.2K pending, ETA ~4.3 hrs)
- Mecum: 329/hr (20.5K pending, ETA ~62 hrs) — free, no Firecrawl cost
- Gooding: 214/hr (1.7K pending, ETA ~8 hrs)

**Known limitations** (inherent, not fixable):
- Old C&B ended auctions (18K cab-fast-discover): spec data permanently gone from live pages
- Bonhams 0% description: JSON-LD doesn't include it, requires JS-rendered body parsing
- Rennlist 7.4% color: forum posts, no structured color field

## 2026-02-26 (Extraction Quality Sprint — Phase 3, post-compression)

### Bonhams Description Fix — 0% → 66% — COMPLETED 2026-02-26 ~22:00

**Root causes found (3 total, not 1):**
1. Firecrawl trigger condition was wrong: `(!hasJsonLd || html.length < 5000)` always false for Bonhams React shell (120KB, has JSON-LD metadata). Firecrawl NEVER ran for fresh pages.
2. Footnotes-only extraction: ~30% of Bonhams lots have a `### Footnotes` section. The other 70% have inline description paragraphs directly after the lot title H2.
3. vehicle_id not linked (fixed in prior sub-session).

**Fixes deployed:**
- `extract-bonhams/index.ts`: Changed `needsFirecrawl` condition from `!fetchResult.cached && !hasLotContent && (!hasJsonLd || html.length < 5000)` to `!hasLotContent`. Now fires Firecrawl whenever we don't have rich markdown, regardless of HTML content.
- `extract-bonhams/index.ts`: Added extraction path B — inline body description: regex captures paragraphs between the lot title H2 (`## **{Year} {Make}...`) and `## Additional information`. Covers lots without Footnotes sections (the majority).
- Result: description rate **0% → 66%** (47/71 lots in first 10 min after deploy). Avg description length 3,564 chars.

**Verified on:**
- 1929 Brough Superior SS100: 4,800-char description from Footnotes section ✓
- 1933 Fiat 508 Balilla: full inline body description extracted ✓  
- 1934 Dodge, 1935 MG Magnette, 1949 Triumph: confirmed having descriptions ✓

### Gooding Throughput Boost — 43/hr → 187/hr — COMPLETED 2026-02-26

- Added crons 233, 234 (gooding-queue-worker-1, gooding-queue-worker-2) in Phase 2
- By Phase 3: confirmed 187/hr actual throughput (was 43/hr round-robin)
- ETA reduced: 36 hrs → 7 hrs for remaining 1.3K pending

### Final Pipeline State (2026-02-26 ~22:00)

| Source   | Pending | Rate/hr | ETA hrs |
|----------|---------|---------|---------|
| mecum    | 54,520  | 828     | ~66     |
| c&b      | 30,486  | 984     | ~31     |
| b-j      | 22,676  | 1,931   | ~12     |
| pcarmarket| 4,963  | 157     | ~32     |
| bat      | 3,550   | 832     | ~4      |
| bonhams  | 2,435   | 573     | ~4      |
| gooding  | 1,317   | 187     | ~7      |

All descriptions now being extracted correctly. Bonhams: Firecrawl fires for every uncached page, both Footnotes AND inline body parsed.

## 2026-02-26

### [competitors] Insert fractional ownership competitor data into import_queue
- Rally Rd: Updated 9 existing records with full VINs, specs, tickers, market_cap, share_price, fractional ownership data
  - Cars: '55 Porsche 356 Speedster, '65 Mustang Fastback, '77 Lotus Esprit S1, '82 Aston Martin V8 Vantage, '85 Ferrari Testarossa, '88 Lamborghini Jalpa, '94 BMW 850CSi, '03 Saleen S7, '06 Ford GT
  - Corrected year: Aston Martin 1978→1982, Ford GT 2005→2006 (per VIN decode)
- TheCarCrowd: Created scrape_source (id: 34c7812c) + inserted 15 UK syndicate vehicles (2 fundraising, 9 active, 3 planned)
- Fraction Motors: Created scrape_source (id: 8d85dde9) + inserted 5 Solana-tokenized vehicles with VINs + SOL token pricing
- Total: 9 updated, 20 inserted (15 TCC + 5 FM), 2 new scrape_sources

## 2026-02-26 — Competitor Intelligence

### [market] Competitor comparison page — MarketCompetitors.tsx
- Built /market/competitors page with real scraped data (not guesses)
- Vercel Edge Middleware for OG tags (Twitter/LinkedIn/iMessage link previews)
- Share button with navigator.share / clipboard fallback

### [market] Competitor research — 3 deep passes
Pass 1: Identified real competitors (dropped Collectable/Otis/Apex Trader — not car platforms)
Pass 2: Scraped Rally WP API (9 cars, VINs, market caps, share prices), TheCarCrowd (15 UK syndicates), Fraction Motors (5 Solana cars with VINs)
Pass 3: Perplexity deep research — Rally $112M raised/$40M AUM/SEC fine, TheCarCrowd own site says NOT FCA-regulated/12.5% fees, MCQ Markets added as new competitor, market size $1.38B total/<$100M AUM combined

### [db] 29 competitor vehicles imported to import_queue
- 9 Rally (VINs, specs, market caps, share prices — all verified)
- 15 TheCarCrowd UK syndicates (Ferrari F430, Porsche 996 GT3 RS, Audi R8, Mercedes SLS, etc.)
- 5 Fraction Motors (VINs: Mustang K-Code, Chevelle SS, GT500, Beetle, Fiero)
- scrape_sources created for TheCarCrowd + Fraction Motors
- All tagged: competitor:true, fractional_ownership:true

### [comms] Briefed 4 teams
- VP Extraction: process 29 import_queue records, VINs listed
- VP Vehicle Intel: use Rally/Fraction Motors prices to validate our NAV accuracy
- CPO: market wide open (<0.3% fractionalized), SDK opportunity outlined
- VP Deal Flow: competitor secondary market structures + Rally SEC precedent

## 2026-02-27

### [deal-flow] Transfer system startup audit — Task 840e4012
- Audited full transfer-automator pipeline (seed_from_auction, seed_from_listing, staleness_sweep, get_transfer, update_contacts)
- Confirmed notify-transfer-parties + transfer-advance both live
- Transfer state: 31,887 total (30,164 in_progress, 1,723 completed), 47,072 overdue milestones
- 150,353 sold auction_events still missing transfers (82.5% of 182,251 total sold)
- Crons 223-227 (transfer-backfill-1 through 5): deactivated, ALL call backfill_transfers_for_sold_auctions(100)
- Assessment: NOT safe to re-enable — would trigger ~300K outbound emails to historical auction buyers/sellers
- Required fix before re-enable: add suppress_notifications param to transfer-automator seed_from_auction
- Blocker: Twilio suspended (negative balance, CFO owns); email (Resend) working
- No duplicate transfers found — idempotency is clean
- Minor bug: get_transfer returns [object Object] on missing transfer (String(error) on Supabase error object)

## 2026-02-27

### [extraction] Import queue backlog investigation — Task 68c9b395
- Investigated 101,935 pending items in import_queue
- **Verdict: Not a stall — was a demand spike.** Bulk ingestion on 2026-02-26 16:00 UTC added 71,174 items in one hour (Extraction Quality Sprint)
- Queue actively draining: ~50/min, ~57,900/day completions; net drain ~28K/day
- No stale locks, only 95 failed items (all normal quality gate rejections: missing year/make/model)
- Platform breakdown: Mecum 51K, C&B 28K, B-J 17.5K, PCarMarket 2.5K, BaT 1.1K
- Mecum workers 3-5 intentionally disabled — rate limiting issue (214 rate-limited skipped items confirms this)
- C&B/B-J cron startup timeouts (~20-30% miss rate) are pg_cron cold-start issue, not data failures
- ETA to clear backlog: ~3.5 days at current drain rate

## 2026-02-27

[platform] VIN search capability (P1 task 4bcca72a)
- Added dedicated "VIN Lookup" toggle widget to Search page — supports full 17-char VINs and partial (≥5 char) prefix/substring search
- Added `GET /api-v1-vehicles/by-vin/:vin` endpoint — exact or partial VIN, public vehicles only
- Added `search_vehicles_by_partial_vin()` DB function (migration 20260227050000) — uses `lower(vin) LIKE lower(...)` to correctly hit the `vehicles_vin_trgm_idx` trigram GIN index (plain ILIKE caused btree scan → timeout on large table)
- Fixed IntelligentSearch: exact 17-char VIN not in DB now shows clear "not found" message instead of falling through to irrelevant text search results

### [frontend] Admin + Onboarding UX overhaul — commit 5a62f7c34
- Login: Sign in/Create account tabs at top (was buried text link at bottom), explicit button labels
- Login: Design system CSS vars for toggle colors (was hardcoded hex), fixed autocomplete attrs
- Login: Post-login redirect goes to / now (was /vehicles → wasted redirect chain)
- OAuth callback: same fix — / not /vehicles
- Admin routes: /admin/proxy-bids + /admin/unified-scrapers (both were 404, now routed + in nav)
- AdminHome: Ralph loading state shows "loading…"/"asking LLM…" text, not morphing button label
- AdminHome: "Refresh" button replaces "Snapshot" (auto-load already runs snapshot on mount)
- AdminHome: auto-load uses max_failed_samples:50 instead of 250 (faster mount)
- Profile: "Get started" checklist on Overview tab for new users with incomplete profiles
- VehicleCollection: empty own-profile state has "Add a vehicle" CTA button (not just text)

## 2026-02-27 — Data Quality Command Center

[data-quality] Full Data Quality Command Center built + deployed — commit 45ec32b2a

### What was built:
- **`data_quality_snapshots` table** — stores periodic snapshots of field completion rates (7-day retention)
- **`compute-data-quality-snapshot` edge function** — TABLESAMPLE 1% → 35 field stats, inserts snapshot row; cron job 303 (*/10 min)
- **`data-quality-workforce` edge function** — priority orchestrator fires 7 enrichment strategies (4 free always-on, 2 LLM gated, 1 valuation); cron job 304 (*/5 min)
- **`DataQualityDashboard.tsx`** — `/admin/data-quality`, real-time field completion bars with trend arrows, ETA to 95%, workforce START buttons, 30s auto-refresh
- **DB functions**: `get_data_quality_field_stats()` (TABLESAMPLE 1%, 25s timeout), `get_pipeline_cron_stats()`, `cleanup_old_quality_snapshots()`

### Current baseline (1,241,147 vehicles):
- make: 98.2%, model: 98.1%, year: 92.9%  (solid)
- listing_url: 85.4%, country: 100%
- body_style: 51.1%, engine_type: 41.6%, heat_score: 41.8%
- mileage: 17.1%, vin: 17.9%, image_url: 18.1%
- city: 2.7%, state: 3.0%  (location gap)
- deal_score: 0.6%, signal_score: 0.2%  (scoring pipeline ramping)
- engine_liters: 0.1%  (very sparse)

### Cron jobs:
- Job 303: compute-data-quality-snapshot (*/10 * * * *)
- Job 304: data-quality-workforce (*/5 * * * *)

## 2026-02-27

### [CFO] Twilio credentials diagnosis + founder escalation
- Diagnosed: auth token missing (NOT negative balance as task stated)
- Twilio account SID confirmed in vendor_accounts
- Balance: $8.31 (degraded, below $20 threshold)
- .env + Supabase secrets: all placeholder values (your-twilio-account-sid)
- Cannot auto-retrieve auth token — requires founder login to console.twilio.com
- SMS cost math: 150K transfers × 2 SMS × $0.0079 = $2,370 → recommend $2,500 top-up
- Founder email sent with exact copy-paste commands for .env + supabase secrets set + test curl
- Test transfer_id ready: 8121d986-f8fc-4aaa-b5f9-2302453f0122
- Crons 223-227 remain paused pending Twilio credentials from founder
- Task 4a3e8f26 marked completed, vendor_accounts updated

## 2026-02-27

### [vp-platform] Fix P0: Vehicle profile infinite loading for anon users (task bda3c25b)
- Root cause: `anon` role has `statement_timeout=3s`. `get_vehicle_profile_data` called `vehicle_price_signal()` (multi-table JOIN) + fetched all images with no LIMIT → exceeded 3s under load → HTTP 500.
- DB migration `20260227210000_optimize_get_vehicle_profile_data.sql`: rewrote function removing expensive subqueries (price_signal, price_history, documents) and capping images at 200. Heavy vehicle: 1.9s → 0.9s (well under 3s limit).
- Frontend: reduced RPC client timeout 8s → 2.5s so client fallback fires before DB kills. Also expanded error message check and switched fallback from `select('*')` to explicit columns.
- Both test vehicles now return HTTP 200 in <1s via anon key. Commit 5ee11e181.

## 2026-02-27

### [transfers] Transfer System UI — operator dashboard + buyer/seller pages
- `/admin/transfers`: Operator dashboard listing 32,762 in_progress transfers, sorted by overdue milestone count
  - Inline expand → full milestone checklist with ✓ Done buttons → calls `transfer-advance:advance_manual`
  - Quick links to buyer/seller views per transfer
  - "Log a Deal" modal for private sales → `transfer-automator:seed_from_listing`
  - Filter by status (in_progress/completed/stalled/cancelled), search by vehicle/handle, pagination
- `/t/:transferId`: Public buyer/seller page, token-accessible (no login required)
  - Vehicle image, price, milestone timeline with completion dates
  - Confirm buttons on current milestone
  - Free-form "Send an update" signal box → `transfer-advance:ingest_signal` (AI classifies)
  - Inbox email contact footer
- AdminShell nav: Transfers added as primary nav item
- Commit: `0f4d8bf09`

## 2026-02-27

### [auth] Auth guard map + enforcement (task e6aa28b8)
- Created `ProtectedRoute` component: shows loading state while auth resolves (prevents null-user crashes), then redirects unauthenticated users to `/login?returnUrl=...`
- Created `RequireAdmin` component: auth + admin role check; on non-admin redirects to `/org/dashboard`
- Created `AuthErrorBoundary`: class-based boundary at App root catches RLS / 401 errors that escape pages → shows friendly "sign in required" card instead of blank page
- Annotated DomainRoutes.tsx with full public / protected / admin route map (60+ routes)
- Protected in vehicle module: `/vehicle/add`, `/:id/edit`, `/:id/mailbox`, `/:id/invest`, `/:id/portfolio`, `/:id/wiring`, `/:id/work`
- Protected in org module: `/org/dashboard`, `/org/create` (browse + profiles stay public)
- Protected in marketplace module: `/market/investor/dashboard`, `/market/portfolio`, `/market/builder`, `/market/contracts`, `/market/bids`
- Protected entire dealer module: `/dealer/*`
- Gated admin module with `RequireAdmin` at route level (stops lazy chunks from loading for non-admins)
- Commit: `86c279ee5`

### [cwfto] Situational Brief — 2026-02-27 ~18:30 UTC
- **P0 FOUND AND MITIGATED**: 30-minute UPDATE on vehicles (`SET auction_source = 'barrett-jackson'`) from normalize-slugs migration was blocking PostgREST schema cache reload. Another agent retrying DROP/CREATE INDEX caused AccessExclusive lock cascade → PGRST002 outage on ALL REST API calls.
- Cancelled 12+ DDL lock-waiters across 4 rounds
- Paused valuation cron jobs 321-325 (run_valuation_batch_by_quality) to reduce lock contention
- Closed stale task: YONO sidecar unreachable (29ede778) — confirmed healthy (tier1 OK, flat=276, zone=41, uptime=463s)
- Reset YONO sidecar redeploy (da504643) to pending — tier-2 training still active (japanese epoch 1/25)
- Filed 3 tasks: P97 vehicles lock fix, P88 re-enable valuation crons, P80 batch migration rule for CTO
- Scheduled next CWFTO loop (P92)

### [fb-marketplace] Comprehensive GraphQL probe + v2 scraper + 5-city production sweep
- **Probe 1**: Tested LSD token, fb_dtsg, User-Agent, doc_ids, full response schema mapping
  - KEY FINDING: No tokens required (LSD, dtsg, cookies) -- GraphQL works bare
  - KEY FINDING: Any User-Agent works (Chrome, Bingbot, Googlebot, curl, empty)
  - KEY FINDING: Zero pagination overlap across 10 pages (240 listings)
  - Full listing schema mapped: 30+ fields, presence rates documented
- **Probe 2**: Tested count, radius, price, year, make filters, cross-city, deep pagination
  - Price filter: WORKS accurately
  - Year filter: BROKEN (effectively ignored -- must filter by title parsing)
  - Make filter: BROKEN (effectively ignored)
  - Radius: WORKS (5km to 500km tested)
  - Max count per page: 24 (hard cap, requesting more still returns 24)
- **v2 scraper**: Rewrote `fb-marketplace-local-scraper.mjs`
  - Removed LSD token fetch (unnecessary HTTP request per city)
  - Batch upserts instead of individual queries
  - Expanded to 55 US metros (from 43)
  - Rate limit retry logic
  - Status mapping (is_sold/is_pending)
- **Production sweep**: 5 cities x 10 pages = 1,200 listings scanned
  - Austin: 21 vintage, Detroit: 31, LA: 44, Chicago: 28, Miami: 20
  - Total: 144 vintage listings upserted, 0 errors, 0 rate limits
  - National vintage rate: ~12% of all vehicle listings
- Updated `facebook-marketplace-extraction.md` with all findings
- Diagnostic scripts: `scripts/fb-graphql-probe.mjs`, `scripts/fb-graphql-probe-2.mjs`

## 2026-02-27 (VP AI — YONO Sidecar Fix)
- [yono] Fixed sidecar "modal-http: invalid function call" — root causes: (1) `@modal.concurrent(max_inputs=10)` is incompatible with `@modal.asgi_app()` in Modal 1.3.2 — removed it; (2) stale 529KB tier-2 ONNX stubs (graph-only, missing .data weight files) crashed containers on startup — deleted from volume; (3) added try/except around ONNX model loading so future incomplete uploads can't crash the server
- [yono] Sidecar redeployed at https://sss97133--yono-serve-fastapi-app.modal.run — /health 200 OK, /classify working (Land Rover correctly identified via british family tier-2 hierarchical inference)
- [yono] Tier-2 families live: american, british, german, japanese, italian, french (6/7 — Swedish still training PID 89338, watcher PID 7390 + PID 796 will auto-upload when done)
- [yono] URL typo documented: task description said sss73133 but actual workspace is sss97133 — .env and Supabase secrets are correct

## 2026-02-27 (VP Extraction — Fix primary_image_url on vehicle creation)

### Task: 5ed3e3b9-bbfd-473e-b522-4c3e9225e30d
**Priority:** 88
**Problem:** 1,671/1,684 vehicles created in last 24h had `primary_image_url = NULL`
**Root cause:** `extract-cars-and-bids-core` and `extract-bat-core` were creating vehicles with image galleries (inserted to `vehicle_images` table) but not setting the `primary_image_url` field on the vehicle record itself. This requires backfill operations and breaks discovery thumbnails.

**Fix applied:**
- `extract-cars-and-bids-core/index.ts`: Added `primary_image_url: extracted.images.length > 0 ? extracted.images[0] : null` to vehicleData
- `extract-bat-core/index.ts`: Added `primary_image_url: images.length > 0 ? images[0] : null` to insertPayload
- Both deployed successfully

**Impact:** 
- New vehicles created by these extractors will now automatically have primary_image_url set from first image
- Eliminates need for backfill scripts
- Enables immediate display of vehicle thumbnails in search/discovery UI
- Prevents the 1,671+ vehicles NULL state from recurring

**Status:** COMPLETED ✓

## 2026-02-28
- [frontend] Demoted AI button in ImageLightbox — hidden by default, shows RETRY on failure, status text for processing/pending, Alt+click power-user reprocess preserved
- [frontend] Added Vision Summary section to sidebar — vehicle_zone, condition stars, photo_quality, damage_flags as red tags, fabrication_stage
- [frontend] Made raw ai_scan_metadata collapsible (details/summary) — collapsed by default for power users
- [frontend] Updated ImageInfoPanel (mobile) with matching Vision Summary section
- [frontend] Replaced ANALYZE NOW button with status-aware display in sidebar
- [frontend] Walk-Around Carousel: horizontal scrollable strip below hero showing best image per zone category in canonical walk-around order (FRONT -> FRONT 3/4 -> DRIVER -> REAR 3/4 -> REAR -> PASSENGER -> INTERIOR -> ENGINE -> UNDER -> WHEELS -> DETAIL), with coverage indicator (X/11 angles), empty dashed placeholders for missing zones, photo counts per slot, click-to-scroll-to-zone interaction

## 2026-02-28

[dedup] Built auto-dedup-check edge function — fires automatically from photo-pipeline-orchestrator on every image INSERT
  - Computes dHash (same algorithm as dedup-vehicle-images), compares against vehicle's existing hashed images
  - If hamming distance <= 5, marks duplicate with provenance priority (user_upload > bat_import)
  - If new image from stronger source, flips — marks OLD image as duplicate (provenance-aware)
  - Non-blocking fire-and-forget from orchestrator Step 8
  - Deployed to production

[dedup] Added provenance display to ImageLightbox info sidebar
  - Shows ORIGINAL badge (green) with photographer attribution when cross_source_provenance exists
  - Shows "Also found on" with source list and dates
  - Shows attribution insight: "uploaded by user before appearing on auction platforms"
  - Shows DUPLICATE badge (red) for duplicate images with link to original

[dedup] Added provenance display to mobile ImageInfoPanel
  - Same provenance/duplicate indicators in mobile-friendly layout

[dedup] Added "dupes removed" count to ImageGallery Story Summary Bar
  - Parallel query counts is_duplicate=true images during load
  - Shows "N dupes removed" in summary bar when duplicates exist
  - Verified all 5 gallery view modes (grid, masonry, list, bundles, zones) correctly filter is_duplicate=true

## 2026-02-28 (Profile Import Flow for /claim-identity)
- [identity] Created `ingest-external-profile` edge function — validates profile URL, upserts external_identities, queues at priority 90
- [identity] Created `process-profile-queue` edge function — claims highest-priority queue items, calls extract-bat-profile-vehicles, sends in-app notification + email on completion
- [identity] Fixed `claim_user_profile_queue_batch` RPC — disambiguated column references (upq alias)
- [identity] Deployed `extract-bat-profile-vehicles` (was local-only, not previously deployed)
- [identity] Registered pg_cron job #335 — process-profile-queue every 5 minutes
- [frontend] Updated ClaimExternalIdentity.tsx — "Not seeing your profile?" import wizard replaces bare "Claim anyway" button; URL paste → instant identity creation → async stats enrichment
- [frontend] Updated Notifications.tsx — added action_url to query and renders as clickable "View →" link
- [identity] Verified end-to-end: skylarwilliams ingested → priority 90 queue → processed → 15 listings found → identity updated

## 2026-03-01

[backfill] Deployed backfill-vin-from-snapshots v1.2.0 — extracts VINs from archived HTML snapshots for vehicles missing VINs
  - Pure regex extraction, no LLM needed — parses BaT listing details, Mecum __NEXT_DATA__, JSON-LD, generic VIN labels
  - 76,570 candidates (vehicles with missing VINs + available snapshots) in pipeline
  - Manual session: 345 VINs found, 194 successfully backfilled, 151 were duplicate records
  - Hit rate: ~65% of candidates with snapshots have extractable VINs
  - v1.2.0 added random offset for cron (prevents re-processing same duplicates)
  - Cron job #345: runs every 10 minutes, batch_size=50
  - ~30 VINs backfilled per cron invocation at current rates
  - Estimated: ~30,000+ recoverable VINs from existing snapshot archive

## 2026-03-04 (ConceptCarz Data Forensics & Cleanup)

[data-quality] Full investigation of 374k ConceptCarz auction result rows (29% of all vehicles)
  - CRITICAL FINDING: 90.7% of sale_price values were fabricated averages, not real hammer prices
  - Proof: real auction prices are always ÷100 (bid increments); CZ prices like $70,156 are impossible
  - 265,215 fabricated prices moved from sale_price → cz_estimated_value column, sale_price nulled
  - 1,962 suspected averages (round but repeated 6+ times) also moved
  - 18,407 rows retained credible sale_price (11,723 likely_real + 6,483 plausible)
  - price_confidence column added: fabricated | suspected_average | plausible | likely_real
  - 25,434 model names cleaned (stripped "Chassis#:..." suffixes)
  - 8,553 garbage rows deleted (make = auction house name: Rm, Bonhams, Mecum, etc.)
  - auction_source mapped for 329k rows across 28 distinct houses (was all "conceptcarz")
  - Top houses: Mecum 92k, Barrett-Jackson 47k, Silver 18k, RM Sotheby's 17k, Bonhams 16k
  - Investigation doc: /Users/skylar/nuke/conceptcarz_investigation.md
  - Cleanup script: /Users/skylar/nuke/scripts/fix-conceptcarz-prices.sh

## 2026-03-07

- [storage] Database storage emergency audit complete — STORAGE_AUDIT.md written
- [storage] Dropped 45 unused/duplicate indexes on vehicle_images (70→33) and vehicles (41→37) — 13 GB freed
- [storage] Dropped 463 empty tables from public schema
- [storage] VACUUM FULL cron.job_run_details (1.2 GB → 8 MB), added daily cleanup cron
- [storage] Deleted 250K failed snapshot rows (zero content, error metadata only)
- [storage] DB reduced: 171 GB → 156 GB (15 GB freed immediately)
- [storage] Built migrate-snapshots-to-storage edge function — moves 79 GB HTML from Postgres TOAST to listing-snapshots Storage bucket
- [storage] Updated archiveFetch.ts readArchivedPage/readArchivedHistory to transparently read from Storage when html column is null
- [storage] Migration cron running (*/5 * * * *, 200 rows/run), ETA ~10 days to complete
- [storage] Target DB size after migration: ~77 GB (55% reduction from 171 GB)

## 2026-03-07

[db-audit] Completed comprehensive empty tables audit — 392 empty tables mapped across 14 categories
  - 934 total public tables, 392 empty (42%), consuming 15 MB total
  - 322 safe to drop, 17 to keep, 13 need investigation
  - Major dead feature groups: Financial/Investment (85), Shop/Workforce (34), Auction/Bidding (23)
  - Also dead: Streaming (10), Insurance/Lending (8), Property (6), Tool Mgmt (10)
  - Report: .claude/reports/empty-tables-audit.md
  - Includes FK dependency mapping, RLS/trigger counts, edge fn + frontend reference counts
  - Migration template included (DO NOT EXECUTE without approval)
  - Real win is TypeScript type reduction (~34% fewer interfaces) not disk space (15 MB)

## 2026-03-07

[data-quality] Deep data quality forensics report completed
  - 13 diagnostic SQL queries across vehicles, vehicle_images, vehicle_events, vehicle_observations
  - CRITICAL FINDING: 499,209 duplicate vehicle rows from BaT URL clustering (84% of "active" count is inflated)
  - 56% of active vehicles have zero images (334,558 out of 592,835)
  - 1,230 phantom makes from case inconsistency (6,737 distinct makes should be ~5,500)
  - data_quality_score is meaningless: 100% of active vehicles score 90+, despite 56% missing images
  - Only 42.4% of active vehicles meet "complete vehicle" benchmark (251,407 of 592,835)
  - $20M Bentley Arnage confirmed as price extraction error (real value ~$39k)
  - 12,887 valuations off by >200% — all from historical vs. current dollar confusion
  - Top 10 ranked improvements with SQL templates written to report
  - Report: .claude/reports/data-quality-forensics.md

## 2026-03-08

[data-quality] Backfilled primary_image_url from vehicle_images for vehicles missing it
  - 26 vehicles updated total (25 from first batch + 1 final manual update)
  - Used is_primary=true images from vehicle_images as the source
  - Key finding: only 26 vehicles had images in vehicle_images but no primary_image_url set
  - The 327K vehicles without primary_image_url genuinely have NO images in vehicle_images at all
  - image_count column on vehicles is accurate (no stale values found)
  - Final state: 0 vehicles with image_count > 0 but no primary_image_url
  - Coverage: 228,967 / 554,447 active vehicles have primary_image_url (41.3%)
  - The remaining 325K without images need images to be ingested first, not backfilled

## 2026-03-09
- [db-security] URL validation CHECK constraints on ownership_verifications (chk_title_document_url_https, chk_license_url_format) — blocks fake protocols like iphoto://
- [db-security] Role CHECK constraint on vehicle_user_permissions (chk_vup_valid_role) — only owner/co_owner/contributor/consigned/previously_owned
- [db-security] Evidence gate trigger on vehicle_user_permissions — replaces narrow enforce_owner_requires_verification with enforce_user_vehicle_evidence (requires photo or document evidence for all roles except previously_owned)
- [db-security] Evidence gate trigger on vehicle_contributors — enforce_contributor_evidence requires photo evidence
- [db-security] Fixed RLS hole: dropped authenticated_can_insert_ownership_verifications policy (allowed any user to create verifications for others)
- [data-cleanup] Deleted 49 forged ownership_verifications (iphoto://local-library URLs) and 49 auto-created vehicle_user_permissions
- [data-cleanup] Re-linked 428 vehicles to Skylar's profile via photo evidence as contributor role
- [db-security] 5 legitimate ownership verifications with real Supabase storage URLs preserved
- [db-security] Fixed vehicle_images_default_attribution trigger — removed auth.uid() fallback that stamped Skylar's identity onto scraped listing images
- [data-cleanup] NULLed user_id on 3,940 craigslist_listing images incorrectly attributed to Skylar
- [data-cleanup] Removed 126 orphaned contributor links (scraped vehicles with no legitimate photo evidence)
- [data-cleanup] Profile reduced from 428 → 302 contributor vehicles (all backed by personal photo evidence)

## 2026-03-10
[training] Confirmed LLM training already on 17.5K dataset (16,643 train / 876 val), checkpoints at 400/450/500
[training] Vision training at epoch 4/30, 51.5% accuracy (up from 28.3%)
[frontend] Committed: search pagination, garage card overhaul w/ tooltips + barcode, non-auto exclusion filter, layout variants
[edge-functions] Committed: universal-search pagination, check-image-vehicle-match expansion, FB scraper image persistence
[yono] Committed: ContextualYONOClassifier (zone/condition/damage/mod/price, zero API calls), contextual training pipeline
[fb-marketplace] Rejected 449 non-auto vehicles (motorcycles, boats, RVs, semis, ATVs, farm equipment, golf carts)
[fb-marketplace] Backfilled 334 missing sale_price from origin_metadata.original_price
[fb-marketplace] Patched scraper to reject non-auto at insertion time (status='rejected' instead of 'discovered')
[fb-marketplace] Cleared 77 stale import_queue items, promoted 331 discovered→pending
[fb-marketplace] Final state: 3,945 valid vehicles (2,171 active + 1,774 pending), 89% with prices, median $4,750
[db] Verified all 31 vehicle triggers enabled, broken trigger already cleaned up

## 2026-03-08 (Search Experience — Rounds 3 & 4)

[search] Round 3 — 5 fixes deployed:
  - Backfilled denormalized image_count/observation_count — 199K vehicles now have counts, triggers handle new data
  - Added applyNonAutoFilters to autocomplete vehicle query in IntelligentSearch.tsx
  - Dropped dead batch_vehicle_counts RPC
  - Replaced all hardcoded hex colors (#000, #3b82f6, #222, #333, #e5e7eb) with CSS variables in IntelligentSearch.tsx
  - Added updated_at to universal-search edge function VEHICLE_SELECT and buildVehicleMetadata
  - Fixed frontend created_at mapping to use updated_at fallback for date sorting

[search] Round 4 — 7 fixes deployed:
  - Added non-auto filters (canonical_vehicle_type) to search_vehicles_smart RPC (all 4 strategies)
  - Added non-auto filters to search_autocomplete RPC (makes, models, vehicles subqueries)
  - Added non-auto filters to search_vehicles_browse RPC (dynamic SQL base WHERE clause)
  - Dropped duplicate p_auto_only function signatures from another agent
  - Created 2 partial indexes: idx_vehicles_auto_lower_make, idx_vehicles_auto_search_vector
  - Fixed #8b5cf6 hardcoded color in SearchResults.tsx → var(--accent)
  - Fixed borderRadius: '2px' in Search.tsx (2 locations) → '0px'
  - Added .catch() to featured vehicles query (unhandled promise rejection)

[search] Build fixes:
  - Removed dead InvestorDealPortal route reference
  - Stubbed missing TradePanel and OrganizationInvestmentCard (deleted by other agents)

[planning] Created 16-agent overnight work plan (.claude/OVERNIGHT_16_AGENTS.md)
  - Covers: make normalization, garbage cleanup, empty table drops (3 agents), edge fn consolidation audit,
    frontend dead feature cleanup, design system sweep, duplicate vehicle analysis, price validation,
    SDK publish prep, search RPC perf tuning, import queue health, snapshot migration, image pipeline health,
    data quality score recalibration

## 2026-03-10

### [frontend] Site fixes
- Fixed mobile bottom nav leaking onto desktop (missing CSS in unified-design-system.css)
- Fixed landing page invisible title (--surface color on --bg background)
- Fixed showcase showing junk (golf carts, commercial trucks) — added quality filters
- Fixed feed showing motorcycles/boats/farm equipment — updated applyNonAutoFilters to block unclassified FB Marketplace
- Fixed vehicle detail page blank (stale Vite dep cache)
- Added "FINDS" sort option to feed toolbar

### [scraper] FB Marketplace signal-based discovery scoring
- Replaced hardcoded collector make/model priority with market-relative signal
- Signal = price anomaly (vs 313K sale comps) + rarity (Y/M/M count) + listing quality
- Created get_ymm_market_index RPC (15,524 Y/M/M price groups)
- Added discovery_priority column to vehicles table (indexed DESC)
- Non-autos now classified at extraction time (MOTORCYCLE, BOAT, RV, etc.) but still stored
- Non-autos get status='rejected' to keep them out of active feeds
- Backfilled signal scores for all existing FB Marketplace vehicles
- Added vehicle type classification (classifyVehicle) + motorcycle model patterns for dual-use makes
- Image download to Supabase storage (FB CDN URLs expire) — user's addition
- Market index loads fresh on every sweep — signal improves as more sales data comes in
- All 4 sweep groups reloaded (3am/9am/3pm/9pm, 58 metros)

## 2026-03-10

[data-quality] Applied alias mappings — Datsun kept separate (collector accuracy), MGB/MGA→MG with model field preserved
[data-quality] Added 35 new canonical makes (Pierce-Arrow, Alvis, Lagonda, Hispano-Suiza, Facel Vega, etc.)
[data-quality] Added aliases for truncated makes (American→AMC, Aston→Aston Martin, Rolls→Rolls-Royce, Diamond→Diamond T, etc.)
[data-quality] Distinct makes reduced from 6,553 → 5,061 (22.7% reduction). Target: ~300.
[data-quality] Remaining: garbage make cleanup (~2,500 vehicles), non-vehicle reclassification (~405), last 108 duplicate pairs

### [frontend] /market route tree cleanup
- Fixed /market/exchange 404: 7 navigate calls across 3 files → /market/segments, added redirect route
- Fixed mobile search input clipping: overflow:hidden → overflowX:auto on FeedStatsStrip, flexShrink:0 on search wrapper
- Deleted MarketMovement.tsx (28-line stub), old MarketSegmentDetail.tsx (admin page), SimpleETFDetails.tsx, marketSystemIntegration.ts (565-line dead service)
- Renamed DebugMarketSegment.tsx → MarketSegmentDetail.tsx (feed-based segment detail)
- Removed /market/dashboard alias, /market/movement route, /market/competitors route (kept file for internal reference)
- Increased FeedToolbar chip padding (3px 6px → 5px 8px) for better mobile tap targets
- Filtered 0-vehicle segments from MarketDashboard segments strip
- Added dismissible first-visit context banner on /market

## 2026-03-14

[frontend] Deep image analysis UI — forensic analysis rendering in ImageExpandedData (condition, surface, degradation, color swatches, modifications, subject, environment, forensic notes), ImageInfoPanel (compact forensic block in tags tab), ImageZoneSection (fabrication_stage badge + deep score support on thumbnails). Commit `80de4709b`.

### [condition] Condition Encyclopedia + Scoring System Rebuild (Complete)
- Phase 1: Ingested 2 OEM service manuals (1982 GMC + 1973 Chevrolet) → 1,111 chunks in service_manual_chunks
- Phase 2: Extracted 1,084 condition knowledge entries (614 failure modes, 470 specifications) into condition_knowledge table
- Phase 3: Expanded taxonomy 69 → 202 descriptors, 45 → 299 aliases
- Phase 4: Fixed condition bridge — zone-aware domain assignment, severity inference from condition_score, case-insensitive flag matching, multi-domain baselines
- Phase 5: Bulk re-bridged 34,389 images → 18,923 ICOs across 4 domains (was: exterior only)
- Scoring: Min=32.5, Max=85.0, Avg=73.7, StdDev=10.1 (was: 35-65, avg=61.7, stddev=7.4)
- Tiers: 127 excellent, 196 good, 46 driver, 4 project (was: all good/driver)
- 25 descriptors in use (was: 3), 4 domains with observations (was: 1)
- Commit: d57b4dc4e + bulk-bridge.py

## 2026-03-15

### [platform-audit] Full Platform Experience Audit
- Tested all 12 API endpoints with real data. 10 work, 2 broken (vision offline, batch auth)
- Published SDK v1.3.1 auth is broken (sends service key as X-API-Key). v2.0.0 fixes it.
- Data quality: 58.5% of active vehicles are skeletons (no image/price/desc)
- Comment sentiment (api-v1-vehicle-auction) rated 9/10 — only analysis tool that delivers answers
- Makes list includes "Coca Cola", "The", "Pair" — data quality issues documented

### [strategy] Extraction → Vision Pipeline Strategy
- Created `extraction-vision-strategy.md` in memory — canonical reference doc
- Phase 1: Documentation first (text-only). Phase 2: Vision blind + contextual. Phase 3: Discrepancy detection
- Descriptions are testimony with half-lives, not data. Trim is forensic (SPID vs badges).
- Comments are rhizomatic (vehicle + user + market + geography + temporal context)

### [library] GM RPO Code Reference Library (15,511 entries)
- Created `gm_rpo_library` table via migration
- Parsed 188-page GM VPPS Nov 2002 PDF → 18,080 entries → 15,511 collector-relevant loaded
- Scraped NastyZ28.com RPO directory → 1,904 unique codes with year ranges (1965-1989)
- Enriched 1,521 RPO entries with first_year/last_year from NastyZ28 data
- Categories: 390 engines, 270 transmissions, 487 primary colors, 654 trim combos, 277 wheels, etc.

### [library] PaintRef.com GM Paint Codes (4,828 scraped)
- Scraped PaintRef.com for 1967-1978 GM paint codes (rate-limited on later years)
- 4,828 color entries with GM WA codes, color names, make/model, paint system cross-refs
- Not yet loaded to DB — pending next session

### [prompt] Description Extraction v2 Prompt
- Wrote 862-line forensic extraction prompt at `prompts/description-extraction-v2.md`
- Temporal decay model: mechanical (fast), cosmetic (medium), structural (slow), provenance (permanent)
- Trim evidence extraction: badges, interior appointments, equipment lists, conflicts
- Vague language detection: flags "recently serviced" with best/worst interpretations
- Cost estimate: $239 Gemini Flash for all 137K BaT descriptions

### [diagnosis] YMM Knowledge Brittleness
- 60% of vehicles (339K of 567K) fail YMM profile lookup
- Root cause: builder coalesces "Camaro Z28" → "Camaro" but runtime constructs "Camaro Z28" key
- Top misses: 1957 Thunderbird Convertible (559 vehicles), 1965 Mustang Convertible (425)
- Fix identified: use (year, make, model) columns with suffix-stripping instead of string key

### [diagnosis] Library Raw Data Audit
- Found 58,864 build posts from 42 forums, 4,922 forum snapshots (464 MB)
- 365K listing page snapshots (48K pending extraction)
- 6 GM service manuals (1,111 chunks), 9,649 LMC truck parts catalog
- 31,585 reference library entries, 128 observation sources with trust scores

### 2026-03-15
- [feed] Recreated vehicle_valuation_feed MV with 5 missing columns (city, state, listing_location, canonical_vehicle_type, has_photos) + all indexes including new idx_vvf_updated_at
- [feed] Fixed FINDS sort button — added finds→deal_score mapping in useFeedQuery.ts
- [feed] Time labels now show "updated Xd ago" when updated_at >> created_at (>24h delta)
- [feed] Added error state UI to FeedPage with RETRY button (was infinite skeleton on failure)

### [admin] Data Pulse v2 — Agent Work Queue
- Killed median prices everywhere (meaningless across mixed platforms)
- Summary bar: +5.3K this week, 79K missing VIN, 41K missing desc, 2K sold no price
- NEW: NEEDS ATTENTION section — ranked priority list of fixable issues by vehicle impact
- Platform cards: velocity arrows, THIS WEEK counts, gap badges (NO VIN/NO DESC/STALE)
- RPC v2: velocity (this_week/last_week per platform), gap counts

### [ingest] FB Marketplace End-to-End Wiring (Session 2)
- Vehicle linking deployed: VIN → vehicle_id, YMM+State → suggested_vehicle_id
- DOM extraction snippet: `scripts/fb-marketplace-dom-extractor.js` (relay store + DOM + meta tags)
- MCP server v0.4.0 committed + pushed to GitHub (npm publish deferred — not product-ready)
- E2E test passed: bingbot fetch → extract → direct ingest → DB verified (1966 Ford Mustang)
- Title parsing fix: strip FB middot/bullet separators before YMM parse
- Legacy URL mode: Firecrawl returns 403 for facebook.com, documented as dead
- **Remaining**: Chrome browser test on real listing page (extension disconnected)

## 2026-03-17

### [connector] Facebook Saved Vehicles Connector — MCP + Browser Extractor
- `scripts/fb-saved-extractor.js` — browser IIFE for facebook.com/saved extraction
- `mcp-server/src/index.ts` — `import_facebook_saved` tool (#12) with extract/submit actions
- `mcp-server/package.json` — v0.5.0
- `mcp-server/README.md` — updated for 12 tools

### [ingest] Enhanced ingest edge function
- Added MODEL_IMPLIES_MAKE (~40 entries) to parseVehicleTitle() — corvette→Chevrolet, mustang→Ford, etc
- Added facebook_saved _source handling (sold→status:sold, auction_status:ended)
- Added facebook-saved source aliases to normalizeVehicle.ts
- Deployed to production

### [vision] analyze-vehicle-image-haiku — NEW edge function
- Claude Haiku vision with zone-specific expert prompts (exterior, interior, engine_bay, undercarriage, detail)
- Snowball context: findings from earlier images feed into later image analysis
- Synthesis pass: aggregates all per-image findings into unified vehicle assessment
- GM truck trim forensics in prompts (Cheyenne indicators: woodgrain dash, tilt column, body side moldings, etc)
- Deployed and tested on 1976 K5 Blazer — 9 images analyzed successfully

### [data] Facebook Saved import results
- 485 vehicles imported (323 sold, 162 active) from FB Saved Items
- 454 timeline events in vehicle_events
- 454 marketplace listing URLs linked
- 1 prototype fully enriched: 1976 K5 Blazer with 9 images, full specs, trim forensics, vision analysis

### [pipeline] Vision pipeline fixes (in progress)
- identify-vehicle-from-image: adding Claude Haiku fallback for broken Gemini/OpenAI
- photo-pipeline-orchestrator: adding analyze-vehicle-image-haiku as YONO fallback

### [db-health] Database Health & Cleanup Session
- **Dropped 8 unused vehicle_images indexes** (~1.58 GB recovered):
  - `idx_vehicle_images_taken_at` (435 MB, 5 scans) — redundant with `vehicle_images_taken_date`
  - `idx_vehicle_images_primary` (424 MB, 46 scans) — redundant with `idx_vehicle_images_vehicle_primary`
  - `idx_vehicle_images_optimization_status` (417 MB, 4 scans)
  - `idx_vehicle_images_category_only` (416 MB, 350 scans) — redundant with `idx_vehicle_images_category`
  - `idx_vehicle_images_position` (297 MB, 2 scans)
  - `idx_vehicle_images_ai_extracted_angle` (3 MB, 2 scans)
  - `idx_vehicle_images_device_fingerprint` (16 KB, 1 scan)
  - `idx_vi_user_unorg_cursor` (0 bytes, 0 scans)
- 24 indexes remain on vehicle_images (was 32)
- **Stale auction transfers**: already resolved (0 in_progress vehicles)
- **Stale crons**: bat-multisignal/bat-queue-worker/micro-scrape-bandaid already removed
- **VACUUM ANALYZE** completed on: vehicles, vehicle_images, vehicle_events, import_queue
- **Empty tables**: 124 found, ~100+ are digital twin ontology (DO NOT DROP). ~12 potentially orphaned flagged for review
- **Stale locks**: zero found (auto-release cron working)
- NOTE: 92 active crons. Possible duplicates: 5x enrich-bulk, 4x batch-extract-snapshots, 3x job_run_details cleanup. Needs review.

### 2026-03-20

### [extraction] archiveFetch Cache Fix — Storage Migration Bug
- CRITICAL FIX: archiveFetch cache lookup only checked `html` column, but 366,627 of 391,539 snapshots (93.6%) had HTML migrated to object storage
- Cache now checks `html_storage_path` and downloads from storage bucket when inline html is null
- Also added fetch_method preference: when caller requests direct fetch, cache prefers direct snapshots over firecrawl ones
- Deployed to 8 functions: extract-barrett-jackson, extract-mecum, extract-bonhams, extract-craigslist, backfill-rmsothebys-descriptions, backfill-cl-descriptions, extract-jamesedition, scrape-ecr-collection-inventory

### [extraction] discover-description-data Fixed — Was Returning "No Vehicles"
- ROOT CAUSE: Vehicle selection query fetched top 20 by sale_price DESC then filtered out already-discovered. Since top 10,981 highest-priced were done, always returned 0.
- Fixed: replaced with RPC-based anti-join query (NOT EXISTS), fast even without price sorting
- Also fixed: API response error handling (was silently swallowing 400/429 errors), upgraded model to claude-3-5-haiku-latest, added parallel processing (5x), time budgets, self-continuation
- 244,902 vehicles remaining for discovery (blocked by Anthropic API credit exhaustion)

### [extraction] batch-comment-discovery Deployed — Was Never Live
- Function existed in codebase but was never deployed. Now live.
- 3,918 vehicles with 5+ comments remaining for analysis
- Also blocked by Anthropic API credit exhaustion

### [extraction] Mecum Image Backfill from Archives
- Fixed extract-mecum to try archived snapshots first (largest direct snapshot by content_length)
- 8 vehicles with 200K+ snapshots processed, 462 images extracted
- 79,434 direct Mecum snapshots exist but 74,953 are empty Next.js shells (112KB) — only 4,480 have full lot data

### [extraction] Barrett-Jackson Re-Enrich Running
- 3,261 B-J vehicles missing descriptions, 311 missing sale_price
- re_enrich pipeline working via cached snapshots (no re-crawling)
- 155 vehicles enriched in session (32 VINs, 1 description, 100+ queued)

### [data-quality] Make Normalization + Price Validation + Dedup + Vehicle Type Classification
- **Make normalization**: 4,372 → 4,136 distinct makes. Fixed ~2,100 vehicles:
  - 1,339 lowercase dupes (ferrari→Ferrari, etc)
  - ~750 split first-word makes (Land→Land Rover, Aston→Aston Martin, Alfa→Alfa Romeo, etc)
  - ~150 model-as-make (Corvette→Chevrolet, Mustang→Ford, Continental→Lincoln, etc)
  - ~100 typos (chebrolet→Chevrolet, Acrua→Acura, etc)
  - ~170 garbage makes nulled (numbers, measurements, non-vehicle words)
  - Top 92 makes (95.3% of vehicles) fully clean
- **Price validation**: Fixed 277 bad prices:
  - 38 year-appended prices (800001967 → 80000) — year was concatenated to price
  - ~106 placeholder $1 prices → NULL
  - ~133 comment-count-as-price errors ($2-$99) → NULL
  - Verified >$10M prices are legitimate (Ferrari 250 GTO, Ford GT40, etc)
- **Deduplication**: 4,850 orphaned skeleton duplicates marked as 'duplicate'
  - Same YMM+price, no VIN, no source events — from bulk imports
  - Kept richest record per group. Active: 296,404 → 291,556
- **Vehicle type classification**: 11,526 vehicles classified, NULL reduced 17,138 → 5,612 (98.1% coverage)
  - CAR +6,793, TRUCK +1,448, SUV +1,152, MOTORCYCLE +499, BOAT +475
  - Fixed Suzuki misclassification (Samurai→SUV, LTZ400→ATV)

### [queue] Import Queue Phase-Out (Agent 7)
- Killed 3 agent hierarchy crons: agent-tier-router (336), sonnet-supervisor (338), haiku-extraction-worker (388)
- Closed 486 stuck items (42 pending, 123 pending_review, 321 pending_strategy, 10 failed) → skipped
- Root cause: ANTHROPIC_API_KEY in Supabase secrets was out of credits ($399.12 spent this period)
- Pushed NUKE_CLAUDE_API to Supabase secrets as ANTHROPIC_API_KEY
- Final state: 17,858 complete, 7,361 skipped, 0 active
- Import queue is fully drained. Agent hierarchy is OFF.

### [extraction] Multi-Model Description Discovery — Local Ollama Pipeline
- NEW: `scripts/local-description-discovery.mjs` — runs description extraction locally via Ollama, zero cost
- Supports any Ollama model: qwen2.5:7b (default), llama3.1:8b, etc.
- Changed description_discoveries unique constraint from (vehicle_id) to (vehicle_id, model_used) for multi-model provenance
- Added npm scripts: `discover:local`, `discover:qwen`, `discover:llama`
- Multi-model validation working: qwen2.5:7b and llama3.1:8b both extract same facts (382hp, 5.5L V8, 13700 miles) with different structures
- Average fields per extraction: Claude Haiku 4.5 = 30, qwen2.5:7b = 30, llama3.1:8b = 29 — consistent signal across models
- Current totals: 9,562 Claude Haiku, 1,257 qwen2.5:7b, 129 Claude 3 Haiku, 41 llama3.1:8b
- 244K+ vehicles remaining — can now batch-process locally at ~8/min with no API cost

### [data-quality] Phase 2: Model Cleanup, Price Bug Fix, Non-Vehicle Archive, Enrichment Pipeline
- **Model field cleanup**: Stripped brand prefixes from ~3,200 models:
  - Land Rover: "Rover Defender 90" → "Defender 90" (3,200+ fixed in 5 batches)
  - Aston Martin: "Martin V12 Vanquish" → "V12 Vanquish" (176 fixed)
  - Mercedes-Benz: "Benz SL500" → "SL500" (156 fixed)
- **FB price parser fix**: Fixed `refine-fb-listing/index.ts` regex that concatenated price+year
  - Root cause: `^\$?([\d,]+)` captured digits across whitespace gap
  - Fix: `^\$?([\d,]+)(?:\s|$)` + sanity check ($100-$50M range)
  - Deployed to production
- **Non-vehicle archive**: 1,675 non-vehicles archived (boats, ATVs, RVs, trailers, farm equipment, buses)
  - Kept 574 high-value motorcycles (Brough Superior, Vincent, sale_price > $20K)
  - Active vehicles: 291,556 → 289,885
- **Enrichment pipeline unblocked**:
  - Found 4,874 enrichable partial skeletons with matching snapshots
  - 3,079 Barrett-Jackson items had NO extraction cron — created cron job 418
  - Fixed platform name mismatch: barrettjackson → barrett-jackson
  - Reset 207 failed queue items to pending
  - Pipeline will clear backlog (~48K items) in ~5 hours
  - 3,500 full skeletons are unenrichable orphaned YMM stubs (no source data exists)

## 2026-03-20

### [user-profile] Skylar Vehicle Profile — Full Ingest Pipeline
- **Safe merges**: 1932 Ford Roadster stub merged into primary (1144 imgs). 1977 K5 Blazer (794 imgs) merged into Blazer primary (1484 imgs → 2278 total). Fixed `merge_into_primary` function (added `recommended_primary` nullable, `exact_listing_url` to match_type check constraint).
- **Location backfill**: All 97 user vehicles set to Boulder City, NV (was NULL on ~55 vehicles).
- **Album mapping**: All 72 iPhoto albums mapped to vehicle IDs. 19 new vehicles created (1959 3100, 1963 Shovelhead, 1964 C20 LWB, 1964 Jaguar XKE, 1967 C10 SWB, 1971 C10 SWB 402, 1972 K10 LWB/SWB, 1973 Charger 360, 1974 K5 Blazer, 1981 DeLorean, 1984 K20 LWB, 1985 K10 SWB Brad, 1987 Nissan Maxima, 1989 Jimmy K5, 2004 F-350, 2005 Ferrari 360 Spider, 2025 Expedition). 15 inactive stubs reactivated with correct models.
- **Suburban dedup**: 22,240 → 13,471 images (8,769 duplicates removed by Apple Photos UUID matching). Disabled per-row triggers during bulk delete for performance.
- **Cron fix**: `iphoto-overnight.sh` updated with `export PATH="/opt/homebrew/bin:$PATH"` and switched to `--sync` mode for iCloud download.
- **Mapper script**: `scripts/iphoto-album-mapper.sh` — explicit album→vehicle_id mapping for all 72 albums, runs iphoto-intake per album.
- **iPhoto intake**: Running in background via mapper script. Albums process sequentially through osxphotos export → HEIC→JPEG → Supabase upload. ~13K photos across 72 albums.
- Vehicle count: 72 active, 38 discovered, 6 inactive, 2 merged = 116 total (was ~100 pre-mapping).

### [extraction] Session Close-Out Summary (2026-03-20)
- archiveFetch cache fix: 93.6% of snapshots now cache-hittable (was 0%)
- discover-description-data: fixed dead query, 244K vehicles now processable
- batch-comment-discovery: deployed (was never live), 3,918 remaining
- extract-mecum: archive-first approach, 462 images backfilled from snapshots
- Multi-model pipeline: qwen2.5:7b grinding at ~100/hr (3,385 done), 0 API cost
- Schema: description_discoveries now (vehicle_id, model_used) unique — multi-model provenance enabled
- Total description_discoveries: 13,121 across 4 models

### [refinery] Comment Refinery — Pipeline Foundation (Phases 1-2)
- **`_shared/commentRefinery.ts`** — Shared utilities: claim density scoring (25 regex patterns across 5 categories), prompt builder for schema-guided per-comment claim extraction, response parser with quote verification, temporal decay computation (paint 2yr, rust 5yr, specs no decay), corroboration engine (cross-refs field_evidence, VIN decode, photos).
- **`comment_claims_progress` table** — Processing tracker: comment_id, vehicle_id, claim_density_score, llm_processed, claims_extracted. Indexes on vehicle, pending queue, density ranking.
- **`compute_temporal_decay()` DB function** — Immutable SQL function for condition claim half-lives.
- **`data_source_trust_hierarchy`** entry — auction_comment_claim at trust level 45 (requires corroboration).
- **`analysis_widgets`** entry — comment-refinery-coverage widget registered.
- **`analyze-comments-fast` claim_triage mode** — Zero-cost regex pre-filter. Tested: 57 comments triaged, 4 passed (7% pass rate). Correctly identifies substantive claims (condition, provenance, ownership) and filters noise (congrats, jokes, short reactions).
- **`batch-comment-discovery` extract_claims mode** — LLM claim extraction pipeline. Gemini 2.5 Flash primary (free), Haiku fallback. Batches 10 comments per LLM call, writes Category A/B claims to field_evidence, updates comment_claims_progress. Self-chaining. **Blocked on LLM credits** — both Anthropic and Google quotas exhausted. Pipeline code is production-ready.

### [refinery] Comment Refinery — First Live Extraction
- **xAI Grok-3-Mini** wired as primary LLM ($0.30/M input, $0.50/M output — ~$0.001/vehicle)
- Fixed JSONB double-encoding in field_evidence (supporting_signals, raw_extraction_data)
- Fixed temporal_anchor NaN when LLM returns "null" string
- Added Category C claim writing via ingest-observation (sightings, ownership, work records)
- **First live run:** 4 comments → 12 claims extracted → 6 field_evidence rows written
  - interior: "original untouched" (conf 100, skylarwilliams)
  - rust: "no signs of rust or mishaps" (conf 100, skylarwilliams)
  - exterior: "excellent survivor, some overspray" (conf 95, skylarwilliams)
  - exterior_damage: "front bumper chips" (conf 80, Archer84)
  - hitch_type: "front hitch receiver" (conf 80, Archer84)
  - trailer_plug: "front trailer plug" (conf 80, Archer84)
- Quote verification working: rejected 1 claim where LLM dropped quotation marks from source text
- LLM fallback chain: xAI Grok → Gemini → Haiku (all wired, tested)
- Estimated full corpus cost: $30-50 via Grok-3-Mini

## 2026-03-21

### [data-quality] Autonomous Data Quality Cleanup
- Archived 24,993 ECR ghost records (no year, no URL, no images, source=unknown)
- Merged 49 JamesEdition URL-variant duplicates (same listing ID, URL differed by appended title)
- Merged 1,224 exact URL duplicate groups across all platforms (6 minor FK errors)
- Archived ~5,000 Bonhams + source skeletons (no year/make/model, no images)
- Generated 26 AI-verified VIN merge proposals via local Ollama (qwen2.5:7b)
  - 17 MERGE (auto-approved >= 85%), 16 executed, 1 FK constraint error
  - 5 SKIP (correctly rejected: fake VINs, mismatched vehicles)
  - 4 REVIEW (held for human judgment)
- Koenigsegg Regera: 84 → 12 active records (case study proving the approach)

### [data-quality] New Scripts
- `scripts/diagnose-duplicates.mjs` — URL normalization diagnostic for any make/model
- `scripts/data-quality-cleanup.mjs` — Phase 1-3: ECR ghosts, JamesEdition dupes, pattern hunting
- `scripts/data-quality-cleanup-phase4.mjs` — Phase 4a-d: exact URL dedup, VIN dedup, skeleton archival
- `scripts/generate-merge-proposals.mjs` — AI-verified merge proposals with `merge_proposals` table
- `merge_proposals` table created (vehicle_a_id, vehicle_b_id, ai_decision, confidence, evidence)

### [architecture] Entity Resolution Rules — Canonical Definition
- Wrote `docs/architecture/ENTITY_RESOLUTION_RULES.md` — definitive rules for all merge/dedup/resolution
- Core principle: vehicle is the entity, URLs are testimony, observations have temporal provenance
- Evidence hierarchy: 4 tiers from definitive (VIN match 0.99) to weak (year+make only 0.30)
- Replaced "merge two profiles" mental model with "link observations to canonical entity"
- Updated CLAUDE.md to reference entity resolution rules before any merge work
- AI verification required for Tier 3+ matches (stored in merge_proposals, auto-approved >= 85%)

## 2026-03-21

### [backend] FB Image Persistence + ARS Tables + Auction Pipeline Cleanup
- **FB Image Backfill**: `scripts/backfill-fb-images.mjs` — downloads expired fbcdn URLs to Supabase Storage. ~24% CDN direct success rate (URLs <2 weeks old still work). Added to package.json as `backfill:fb-images`. Running in background against 6,781 vehicles.
- **vehicle_submissions table**: Created via migration. Completes the ARS table trio (auction_readiness 2,142 rows, photo_coverage_requirements 20 rows, vehicle_submissions 0 rows).
- **persist_auction_readiness()**: Verified working end-to-end. Test on 1977 K5 Blazer: composite_score=45, tier=EARLY_STAGE, 83 photo score, actionable coaching gaps.
- **MCP tools verified**: `get_auction_readiness`, `get_coaching_plan`, `prepare_listing` — all call persist_auction_readiness and return real data.
- **Stale auction events cleaned**: 7,353 → 2,030 truly active events across 12 platforms. Batch-updated 5,323 stale events (ended_at in past or platform stopped syncing).
- **sync-live-auctions cron fixed**: Job 109 updated from `skip_vehicle_sync: true` → `false`. Now creates/links vehicle records during discovery. Runs every 15 min.
- **BaT pipeline confirmed live**: 177 active BaT events, latest update 18 min ago. sync-bat-listing, sync-live-auctions, score-live-auctions all running on cron.

### [auction-pipeline] Live Auction Sync — Full Overhaul
- **Root cause found**: `sync-live-auctions` ran with `skip_vehicle_sync: true` → vehicles table never updated with live auction data. Only vehicle_events got bid snapshots.
- **BaT has 931 live auctions** (scraped from `auctionsCurrentInitialData`) — we had 47 in vehicle_events. Now 5,769 truly live in vehicles table.
- **Timeout fixed**: Rewrote `syncToDatabase()` to use upsert instead of lookup+update. BaT sync dropped from 55s+ timeout to **3.4 seconds**.
  - Old: 5 URL-lookup queries (200 each) + 931 individual UPDATE calls → timeout
  - New: 10 upsert batches of 100 → 3.4s total
- **Cron split**: Single cron replaced with per-platform crons:
  - Job 109: BaT every 15 min at :00 (vehicle sync enabled)
  - Job 422: Collecting Cars every 30 min at :07/:37
  - Job 423: Cars & Bids every 30 min at :22/:52
- **Stale vehicles cleaned**: 1,559 ended BaT + 177 C&B + 153 CC vehicles marked `sale_status='ended'`
- **Collecting Cars**: Re-synced, 148 live auctions in DB
- **Barrett-Jackson**: extract-barrett-jackson returning 400 on every call — needs investigation
- Function redeployed: `supabase functions deploy sync-live-auctions --no-verify-jwt`

### [llm-infrastructure] Local LLM Setup + Enrichment Pipeline
- Downloaded DeepSeek R1 32B, Qwen3 30B-A3B, Kimi K2.5 cloud to SSD
- Created `nuke` Ollama model (fat system prompt with full platform knowledge)
- Fine-tuned `nuke-agent` on market intelligence data (loss 0.084, 2.75 epochs)
- Merged LoRA weights + exported GGUF (4.7 GB Q4_K_M)
- Built unified LLM router (`_shared/llmRouter.ts`) — 13 models, 8 providers, task-based routing
- Migrated haiku-extraction-worker, sonnet-supervisor, agent-tier-router to new router
- Created `agentTiers.ts` backward-compat shim (23+ importers unbroken)
- Added agent_tier/agent_model/agent_cost_cents provenance to vehicle_observations + ingest-observation
- Created llm_cost_tracking table
- Built + tested overnight-enrichment.mjs: 490/500 enriched, 0 errors, 9.1/min, $0
- Kicked off 2000-vehicle enrichment run (PID 49234, ~3.5 hrs, $0)

### [library] Papers + Atlas + Dictionary + Almanac
- PAPERS: Entity Resolution Design (why three-pass cascade, decision record)
- PAPERS: Trust Scoring Methodology (source hierarchy, decay model, contradiction handling)
- PAPERS: Market Intelligence Patterns (7 empirical findings from 304K vehicles)
- PAPERS: Enrichment Rules (ground truth for making data better)
- ATLAS: Scraping Sources (every source with access method, trust, rate limits)
- DICTIONARY: Enrichable Fields (13 unowned fields with rules)
- DICTIONARY: LLM Infrastructure Terms
- ALMANAC: Platform Metrics 2026-03-20 snapshot
- ENGINEERING MANUAL Ch.9: Local LLM Infrastructure

### [training] Modal Fine-Tuning Pipeline
- export_nuke_market_intelligence.py — cohort comparisons, gap analyses (3,213 examples)
- export_squarebody_intelligence.py — all 73-91 GM trucks (3,788 examples)
- modal_nuke_agent_train.py upgraded: Telegram dispatch, GGUF export, --action full pipeline
- Training data on Modal volume: /data/nuke-agent/ and /data/nuke-squarebody/

### [phase-0] Foundation Fixes
- Phase 0.3 DONE: agent_tier, extraction_method, raw_source_ref on vehicle_observations
- Phase 0.4 DONE: CHECK constraint already includes pending_review/pending_strategy

### [backend] FB Image Second Pass — Investigation Complete
- **1,688 images recovered** in first pass (CDN direct download, 24.9% success rate)
- **5,091 remaining** with expired CDN URLs — curl to FB listing pages works but rate-limited (~10 req/IP window)
- Node.js fetch gets login-walled by FB TLS fingerprinting — must use curl subprocess with clean env
- `marketplace_listings.all_images` also stores expired CDN URLs (same tokens)
- **Best path: re-run fb-marketplace-local-scraper.mjs** which uses GraphQL doc_id at scale (residential IP, proven at 58 metros). v3.0 already persists images via downloadAndStoreImage.
- Added curl subprocess + clean env + rate limiting to backfill script for future use

### [auction-pipeline] Stale Auction Cleanup Automation
- Created `cleanup_ended_auctions(batch_limit)` SQL function — marks auction_live vehicles as ended when auction_end_date has passed (10-min grace for soft-close)
- Cron job 424: runs hourly at :05 (`SELECT cleanup_ended_auctions(500)`)
- First run cleaned 42 stale auctions

### [auction-pipeline] Barrett-Jackson — Not Broken
- extract-barrett-jackson returns 400 when called without body params (expected behavior)
- BJ cron (job 418) calls batch-extract-snapshots, not extract-barrett-jackson directly
- Extractor v2.0.0 working: 29,614 BJ vehicles, 90.3% price coverage

### [auction-pipeline] Cars & Bids Sync — Restored
- Tested sync-live-auctions with platform=cars-and-bids: 197 live auctions synced in 10.4s
- Cron job 423 created at :22/:52 schedule

### [data-quality] Phase 1 Bug Fix — Hero Fingerprint FK Violation
- `compute-hero-fingerprints.mjs`: Added FK violation retry (NULL image_ids on constraint error)
- Restarted 50K batch (PID 30637), 8,262 fingerprints computed before fix applied
- FB pipeline complete: 192 linked, 124 new vehicles, 299 stubs cleaned

### [refinery] Comment Refinery — Scale Run + Frontend Wiring
- **Batch triage:** 22,285 comments across top 50 BaT vehicles (by comment count). 6% pass rate.
- **Local Ollama extraction:** 1,232 comments processed via qwen2.5:7b, 573 claims extracted, 69 field_evidence rows, $0 cost.
- **Vehicles processed:** Ferrari LaFerrari, 1971 240Z ($310K sale), Mercedes 300SL Gullwing (restoration costs $200K-$600K), BMW 507, Corvette L88 (427/560hp), Ferrari F40, Porsche 959, Singer 911, Sherman M4A1 tank, BMW M3 E30, Shelby GT350, Porsche 356C — crown jewels of BaT.
- **Frontend wiring:** Added `auction_comment_claim` to useFieldEvidence trust hierarchy (level 45). Dossier panel already renders field_evidence with provenance drawers — comment claims will show alongside listing data.
- **Prompt fix:** field_name now constrained to exact dossier vocabulary (engine_type, mileage, transmission, etc.) — prevents piped multi-field names that don't match frontend.
- **Scripts:** `scripts/refinery-triage-batch.mjs` (batch triage by vehicle), `scripts/refinery-extract-claims.mjs` (local Ollama extraction). Both production-ready.
- **Known issue:** ingest-observation returns non-2xx for Category C claims (provenance/sightings). Fix needed.
- **Re-extraction needed:** First 47 vehicles have messy field_names from pre-fix prompt. Re-run with fixed prompt.

### [feed] Feed Ranking Overhaul — Auctions Now Dominate
- **Root cause**: `vehicle_valuation_feed` MV used `v.discovery_source` which was NULL for 5,344 live auctions (sync writes to `platform_source` not `discovery_source`). All auctions scored 50, FB scored 120.
- **Fix**: Rebuilt MV with `COALESCE(v.platform_source, v.discovery_source)` and new ranking:
  - Live auction: +200, BaT source: +100, CC/C&B/Mecum: +80, FB: -30
  - BaT live auctions now score 350 vs FB at 120
- **Feed-query CDN filter**: Thumbnail resolution now skips expired fbcdn/scontent URLs — no more "IMAGE UNAVAILABLE" cards
- **Non-auto filter**: FB vehicles with null `canonical_vehicle_type` excluded (boats/RVs/trailers)
- **MV refresh cron**: Job 425, every 15 min
- Deployed: `feed-query`, `sync-live-auctions`

### [feed] Materialized View — Missing Refresh Cron Found
- `vehicle_valuation_feed` had NO cron job refreshing it — last autoanalyze was March 19
- New vehicles were invisible to the feed for 2 days
- Created cron job 425: `REFRESH MATERIALIZED VIEW CONCURRENTLY vehicle_valuation_feed` every 15 min

## 2026-03-21

### [design] Header rework — one row, three zones, 40px
- Eliminated 4-variant header system (command-line, segmented, two-row, minimal)
- Single layout: NUKE wordmark | AIDataIngestionSearch | user capsule
- Deleted 5 files: 4 variant layouts + useHeaderVariant hook
- Removed toolbar slot from AppLayoutContext
- Moved VehicleTabBar and PageHeader into content area
- Removed variant picker from UserDropdown and AppearanceSpecimen

### [design] Vehicle profile fixes
- Empty spec rows hidden (no more "—" for null fields)
- Vehicle dossier identity block hidden (was repeating YMM from badges)
- Incomplete profile banner minimized to single-line indicator
- Gallery thumbnails default to contain (stop cropping)
- VehicleSubHeader badge bar visible via CSS swap (VehicleHeader hidden but mounted)

### [library] 2,862 lines across 9 files
- Discourse: The Header (471 lines) — naming, nesting, agentic-first, timelessness
- Discourse: The Bridge (414 lines) — design audit, physical-digital bridge, three user modes
- Discourse: The Audit (400+ lines) — live site problems cataloged with fixes
- Design Book Ch. 1: Foundations (253 lines) — why Arial, why sharp corners, why 8px, Bloomberg/Win95
- Design Book Ch. 5: The Header (259 lines) — implementation spec
- Contemplation: The Permanent Interface (143 lines) — what survives, what dies
- Contemplation: Click Anxiety and Digital Trust (177 lines) — psychology of interface trust
- Contemplation: The Three Users and the Finder (285 lines) — savant janitor, archivist, browser
- Paper: The Agentic Header (235 lines) — navigation vs intent expression
- Dictionary: 17 new terms with intellectual-shelf-depth definitions

### [mistakes] Production breakage
- hasImages:true default emptied the feed (most vehicles lack imported images)
- Removing VehicleHeader from render tree broke profile data flow
- Three broken pushes to production without local testing
- Lesson: branch, local dev, verify, then merge

### [wiring] Squarebody Wiring Layer Overlay - Sprint 1 (partial)
- Created 10 new tables: wire_specifications, connector_specifications, device_pin_maps, factory_harness_circuits, upgrade_templates, upgrade_circuit_actions, upgrade_new_circuits, vehicle_wiring_overlays, vehicle_circuit_measurements, vehicle_custom_circuits
- Seeded wire_specifications: 11 types (GPT through MIL-W-22759/44 and PTFE)
- Seeded connector_specifications: 12 families (Weatherpack through Deutsch Autosport AS)
- Seeded device_pin_maps for M150: ALL 120 pins (Connectors A/B/C/D, 34+34+26+26)
- Seeded device_pin_maps for PDM30: 39 pins (30 output channels + CAN + power + digital inputs)
- Plan doc: .claude/plans/lazy-knitting-harp.md
- Migration file: supabase/migrations/20260322200000_wiring_layer_overlay.sql
- REMAINING: factory_harness_circuits seed (80+ squarebody circuits), pipeline_registry, TOOLS.md update
- Seeded 71 squarebody factory harness circuits (51 standard + 20 option-dependent)
  - 10 systems: lighting(18), accessories(13), engine(10), body(6), fuel(5), gauges(5), starting(5), ignition(4), charging(3), cooling(2)
  - 26 circuits with documented failure modes and severity
  - Options: AC, dual fuel tanks, power windows/locks, cruise control, TBI (1987)
- Registered all 10 tables in pipeline_registry
- Updated TOOLS.md with Wiring Layer Overlay section
- SPRINT 1 COMPLETE

### [wiring] Build Manifest — 77 K5 Blazer (115 devices, 347 endpoints, 60% avg)
- Created vehicle_build_manifest table with sourcing fields (difficulty, lead_time, supplier_type, supplier_contact)
- Populated 115 electrical devices across 12 categories for K5 vehicle e04bf9c5
- 67 have real part numbers, 101 have endpoint/pin counts, 99 have prices
- All data from web research agents (ACDelco, Dorman, Truck-Lite, United Pacific, Dakota Digital, AMP Research, Aeromotive, Motec, Kicker, RetroSound, Optima, Painless, AutoMeter, etc.)
- 10 micro-suppliers registered as catalog_sources (Engineered Vintage, Delmo Speed, Davis Off Road, JL Fabrication, Far From Stock, Desert Performance, Tulay Wire Werks, Retrofit Innovations, E-Stopp, Wilwood)
- Ingested Desert Performance invoice (Howard Barton coupe) — real Motec pricing
- Read 4 NUKE LTD invoices (SW77002-SW77006) for K5 build — $120K+ documented spend
- Key architectural insight: ECU model is a COMPUTED requirement from I/O count, not a fixed choice. Every build manifest change recomputes the entire harness specification.

### [auction-pipeline] Auction Thumbnail Pipeline — Images on Every Card
- **Backfilled 4,753 live auctions** with `primary_image_url` from `origin_metadata.thumbnail_url`
  - 4,619 BaT thumbnails (bringatrailer.com WordPress static URLs)
  - 134 CC thumbnails (images.collectingcars.com CDN)
- **Feed-query pass 3** serves these URLs directly — no Supabase Storage download needed
- **Approach:** Direct URL reference, not download. BaT/CC URLs are stable (WordPress/CDN), unlike FB CDN.
- **Going forward:** `sync-live-auctions` now sets `primary_image_url` in the vehicle upsert payload. Every new auction gets a thumbnail automatically.
- **vehicle_images insert blocked** by unknown trigger/RLS — primary_image_url works as fallback. vehicle_images backfill deferred.
- **Result:** Feed shows Dodge Viper, De Tomaso Pantera, Porsche 911 etc. with actual images instead of "NO PHOTO"

### [wiring] Factory Circuit Validation Against GM Service Manual
- Found 3,406 service_manual_chunks already OCR'd in database (GM 1973 Light Duty Truck Service Manual)
- Discovered GM Electrical Circuit ID Table (Section 8C, pages 46-51) — 500+ circuits with exact wire colors
- Validated all 71 squarebody factory harness circuits against GM source data
- CORRECTED 11 wrong wire colors: neutral safety (YEL not PPL), fuel gauge (PNK not DK BLU), horn feed (DK GRN not BLK), tachometer (WHT not BRN), radio feed (YEL not PNK), headlight hi-beam flip-flopped, window circuits, door lock circuits
- 0 circuits remain unsourced — every row now cites a GM Service Manual section
- ProWire connector prices updated in catalog_parts (19 rows: DTM $3-13, Superseal kits $8-20, M150 complete kit $56)
- Publication pages (41,592) confirmed as Polo Lifestyles magazines — NOT relevant to wiring

### [wiring] compute-wiring-overlay edge function — LIVE
- Deployed and tested against K5 Blazer (e04bf9c5)
- Computes from 115-device build manifest: 96 wires, 744 ft total, 15 PDM channels
- ECU requirement: M150 (28 outputs, 22 inputs)
- PDM channel auto-assignment with overload detection
- Caught and fixed: alternator/starter/battery/brake booster/fuel pump/amplifier are NOT PDM-controlled (direct-wired with relays)
- Deterministic wire color assignment by function group
- Wire gauge auto-selection from amperage + length with voltage drop check
- Alternator sizing from total continuous current draw
- Zero warnings on clean run
- pdm_controlled flag added to vehicle_build_manifest

### [wiring] Thread completions
- THREAD 1: Build manifest 0% devices eliminated — 115/115 have data, 67% avg (was 60%)
  - All power_draw_amps filled, all pdm_controlled flags set
  - PDM channel grouping: markers_clearance(8), park_tail(4), interior_courtesy(5), backup(4), turn_brake L/R
  - Recompute: 30/30 PDM channels, 0 overflow (was 17), 1 headroom warning
- THREAD 3: GM Circuit ID table extracted — 109 circuits in gm_circuit_identification table
- THREAD 5: Invoice ingestion — 33 prices from Desert Performance #1190 in invoice_learned_pricing
  - Real Motec prices: M130 $3,500, PDM30 $3,140, LTCD $844, GT101 $80, RBD-190 $300
  - Labor: $65/hr, dyno $750 flat
- THREAD 6: Compute engine improvements
  - PDM channel grouping (shared channels for low-current devices)
  - PDM headroom warning when channels near capacity
  - pdm_channel_group column on vehicle_build_manifest
  - 3 redeployments of compute-wiring-overlay, all clean

### [wiring] Knowledge persistence — The Wiring Book
- Created docs/wiring/ with README.md (table of contents, 15 chapters + 4 appendices)
- Created WIRING_SYSTEM_KNOWLEDGE.md — complete reference for any agent working on wiring
- Written: Ch1 Workshop Model (1,800 words), Ch3 Tier System (2,200 words)  
- Added wiring system summary to MEMORY.md
- Updated HANDOFF.md with drill-to-bedrock status on 10 threads
- Created .claude/plans/wiring-drill-plan.md with 7 execution threads
- Structure ensures next agent has full context without this conversation

### [wiring] Client-side compute engine + sandbox UI + output generators
- overlayCompute.ts — Pure TypeScript compute engine, runs client-side <5ms
  - ECU OPTIONS (M130/M150/M1 with cost/headroom/bottleneck analysis)
  - PDM OPTIONS (PDM15/PDM30/2×PDM15/PDM30+PDM15 with channel fit)
  - Configuration matrix: all valid ECU×PDM combos sorted by cost
  - Delta computation: what changed between two computations
  - Wire color assignment by function group
  - All from harnessCalculations.ts foundations
- useOverlayCompute.ts — React hook: addDevice/removeDevice/updateDevice triggers instant recompute
  - Quick helpers: addSensor, addLight, addMotor
  - Delta tracking for flash-on-change UI
- WiringOverlaySandbox.tsx — Interactive sandbox component
  - Quick-add buttons for 19 device templates (sensors, actuators, lighting, body/accessories)
  - Status bar with live device/wire/ECU/PDM/cost/warnings
  - Delta flash showing what changed on each add/remove
  - ECU options panel showing all models with fit/headroom
  - PDM channels panel with load per channel
  - Wire list view
  - Device list with remove buttons
  - Warnings panel
- WiringSandbox.tsx — Page wrapper, loads manifest from Supabase, route at /:vehicleId/wiring/sandbox
- generateCutList.ts — Wire-by-wire bench document with sections (engine/exterior/interior/chassis/audio)
  - Plain text export for printing
  - Wire purchase summary with spool size recommendations
  - Shielded and twisted pair callouts
- generateConnectorSchedule.ts — Pin-by-pin output for ECU connectors and PDM channels
  - Plain text export
  - Groups by connector (A=outputs, B=inputs, C=comms)
  - PDM channel assignments with load and overload warnings
- generateBOM.ts — Full bill of materials linked to catalog
  - Motec system section with computed ECU+PDM+connector kit
  - All device categories with part numbers and pricing
  - Wire and consumables estimation
  - Labor hours estimate (0.5 hr/wire × wire count)
  - Grand total with labor
  - Purchased vs unpurchased tracking
  - Plain text export

### 2026-03-23 — Auction System Deep Audit

[auction/bids] Fixed bat_bids recording — 965 bid snapshots per sync restored
  - Root cause: redundant 2nd query to vehicle_events failed with 500-UUID .in()
  - Simplified to use id from first query directly
  - Dropped bat_bids_bat_listing_id_fkey (live auctions don't have bat_listings entries)
  - Migration: drop_bat_bids_listing_fk_for_live_sync

[auction/images] Fixed vehicle_images photo pipeline trigger for BaT imports
  - Added ai_processing_status: "pending" to extract-bat-core insert objects
  - Photo pipeline trigger now fires for newly imported auction images

[auction/cab] Fixed C&B auction end date handling
  - Added end-time parsing from page HTML data
  - Added cleanup step: marks expired auctions as ended after each sync cycle

[auction/vehicles] Fixed listing_url unique index enforcement
  - Soft-deleted 4,885 duplicate vehicles (keeping most complete per listing_url)
  - Recreated idx_vehicles_listing_url_unique (was indisvalid=false)
  - Index now valid and enforcing uniqueness

[auction/predict] Restored hammer price prediction pipeline
  - Created missing _shared/predictionEngine.ts (deleted during triage)
  - Fixed column mapping: vehicle_event_id → external_listing_id
  - Fixed end_date resolution (ended_at fallback)
  - Added factors object to PredictionOutput for reporting
  - 3 existing crons running: predict-all (30m), final-hours (10m), score (30m)
  - Verified: 2 new predictions stored successfully

[auction/ars] Audited ARS system — FULLY IMPLEMENTED (not spec-only)
  - compute_auction_readiness() SQL function exists with all 6 dimensions
  - 124,143 vehicles scored (avg 22.6, range 5-69)
  - Tier distribution: 112K DISCOVERY_ONLY, 16.7K EARLY_STAGE, 153 NEEDS_WORK
  - Photo dimension correctly wires YONO zone classification
  - coaching_plan JSONB generated with priority-ranked gaps

[auction/comments] Audited comment extraction — wiring exists
  - sync-bat-listing triggers extract-auction-comments for auctions ending within 24h
  - restore-bat-comments cron runs daily at 2 AM
  - backfill-comments self-continuing batch available
  - No changes needed — system is functional

[audit/remaining] Sections 8-9 (widgets, coaching frontend, packager, submission) documented but not implemented
  - 12 analysis widgets have near-zero coverage (3 vehicles each)
  - Coaching data IS computed but no frontend panel exists
  - Listing packager and submission automation are spec-only

### [wiring] M130 viability proven — $2,000 saved through data correction
- Reclassified 20 switch/digital devices into proper categories:
  - ecu_digital_input (4): brake switch, A/C pressure switches, VSS
  - ecu_crank_cam (2): crank + cam dedicated inputs
  - pdm_input (9): headlight/turn/wiper/blower/ignition/door switches, reverse, tcase
  - standalone_switch (4): window switches, lock switch, neutral safety
  - standalone_module (1): hazard flasher
- Fixed half-bridge counting: only ECU-driven motors counted (throttle body), not PDM-controlled motors
- Fixed CAN bus counting: 1 bus with multiple devices, not count of CAN devices
- Added M130 ECU to compute engine with verified specs (racespeconline.com):
  - 8 P&H inj, 8 LS ign, 6 HB, 8 AV, 4 AT, 7 UDIG, 2 knock, 1 CAN
  - 2 connectors (34+26 Superseal), 107×127×39mm, 290g, $3,500
- Added M130 pin map to device_pin_maps (60 pins across 2 connectors)
- ECU selection now per-type comparison (not total I/O count)
- Result: M130 fits the K5 build — 8/8 inj, 4/7 dig, 1/6 hb, 1/1 CAN
- Cost impact: M130 $3,500 vs M150 $5,500 = $2,000 saved

### [wiring] Cut list edge function deployed and tested
- generate-cut-list deployed — produces printable wire-by-wire bench document
- K5 output: 110 wires, 805 ft, 7 sections (engine/exterior/interior/chassis/audio/power/misc)
- Wire purchase summary: 11 gauge/type combinations, spool recommendations
- Saved to docs/wiring/output/K5_cut_list.txt (157 lines)
- Supports JSON and text format output
- Text format is directly printable for the wire bench

### [wiring] BOM edge function deployed
- generate-wiring-bom deployed — full bill of materials with catalog linkage
- K5 output: $19,966 total (parts $16,391 + labor $3,575 at $65/hr)
- ECU: M130 ($3,500) — computed, not assumed
- 94 items priced, 18 need quotes, 30 purchased, 85 needed
- Saved to docs/wiring/output/K5_bom.txt
- Deep sprint Batch 1: 2 of 3 output functions deployed (cut list + BOM)
- Remaining: connector schedule edge function

### [wiring] Book chapters written
- Ch5: Build Manifest — signal type classification, M130 discovery, PDM channel grouping, direct-wired devices
- Ch6: Compute Engine — I/O requirements, ECU selection, PDM assignment, wire specs, delta computation, file reference
- Ch7: Motec Ecosystem — M130/M150/M1 specs with I/O tables, PDM configs, LTCD, C125, CAN architecture, pin map status warnings
- Ch8: LS3 Sensors — complete ACDelco part numbers for every sensor/actuator, connector types, critical compatibility notes (D510C not D585, 6-pin not 8-pin throttle, EV6 not Multec)
- Total book progress: 6 of 15 chapters + appendices written (Ch1, Ch3, Ch5, Ch6, Ch7, Ch8)

### [wiring] All three output edge functions deployed and tested
- generate-connector-schedule deployed — pin-by-pin for M130 (Connector A + B) and PDM30
  - M130 Connector A: 8 injectors + 8 coils + crank/cam + grounds/power assigned. 8 unused (A19-A26 half-bridge)
  - M130 Connector B: 2 knock sensors assigned. 23 unused. Massive input headroom.
  - PDM30: 30 channels assigned by current draw. All with part numbers cross-referenced.
  - Saved to docs/wiring/output/K5_connector_schedule.txt
- 3 more factory circuit corrections: CHARGE_SENSE (BRN→DK BLU), HEATER_BLOWER (ORN→PPL), IGN_RUN (correct reference)
- Total factory circuit corrections this session: 14
- Standardized ORG → ORN abbreviation across all circuits
- Cross-referenced 24 circuits against gm_circuit_identification: 19 MATCH, 2 PARTIAL, 3 MISMATCH (all fixed)

### [manhunt] Service Manual Manhunt System
- Created `manhunt_searches` table for tracking systematic documentation searches
- Built `scripts/manhunt-service-manuals.mjs` — local script with 3 source modules:
  - **Archive.org**: broad keyword search with scoring, year-range matching, PDF download + upload
  - **NHTSA**: complaints + recalls API (free, no auth needed)
  - **Ford Heritage**: browse + Archive.org mirror fallback
- Fixed `link_document_to_specs` trigger (NULL model crash on library_documents insert)
- 5 npm scripts: `manhunt`, `manhunt:top50`, `manhunt:dry`, `manhunt:ford`, `manhunt:tsb`
- First run results: 14 documents created, 25 libraries now have docs (was 15), 138 MB in storage
- Rate limiting: 1 req/sec search, 5s metadata, 10s download. Max 100 searches + 20 downloads/run
- Handles Archive.org borrowable items (401/403), restricted items, connection timeouts
- Search result caching per make (6 broad queries cached, reused across year-specific libraries)

### 2026-03-22
### [patient-zero] Content Engine — 7 content types on weekly rotation
- Migration: content_type, thread_posts, source_data columns on patient_zero_queue + patient_zero_calendar + patient_zero_chart_templates tables
- Content router: actionGenerate now dispatches by day-of-week calendar (Mon=save, Tue=chart, Wed=vehicle, Thu=shop_photo, Fri=chart, Sat=retrospective, Sun=thread)
- Chart engine: `_shared/chartGenerator.ts` — QuickChart.io URL builder with Nuke design system (Arial, Courier New, zero radius, #f5f5f5 bg, 11-color palette)
- 8 chart templates seeded: price-trend-by-make, disappearance-velocity, estimate-vs-actual, auction-platform-comparison, bid-count-distribution, year-tier-pricing, weekly-marketplace-flow, geographic-price-map
- Data pipelines: `_shared/contentQueries.ts` — querySaveData (fb_saved_items × marketplace_listings), queryRetrospectiveData (auction vs marketplace delta), queryMarketObservationData, queryVehicleData, queryThreadData, queryChartData
- Thread publishing: X gets sequential reply chain (max 8 tweets, 1.5s delays), non-X platforms get single-post fallback
- Type-specific LLM prompts: saves=regretful, charts=clinical, retrospectives=wistful, threads=authoritative
- New Telegram command: /pztype [type] for calendar override
- TOOLS.md updated with content types, calendar, new tables
- Deployed and verified: function compiles clean, responds correctly

### 2026-03-23
### [auction] Widget coverage backfill system
- Added `backfill_auctions` action to analysis-engine-coordinator
- Creates `analysis_queue` table + `claim_analysis_queue_batch` RPC (were missing)
- Queries ARS-scored vehicles with no analysis_signals, processes through all enabled widgets
- Tested: 5 vehicles × 14 widgets = 70 signals created, 0 failures
- Cron: `analysis-widget-backfill` every 10min, batch_size=50

### [auction] ARS market_score wired to analysis_signals
- Fixed `compute_auction_readiness()` — 5 column mismatches corrected:
  - exterior_color → color, engine → engine_type, flaws → known_flaws
  - zone_label → vehicle_zone, library_documents → vehicle_documents
  - condition_report → condition (enum value)
- Added analysis_signals bonus: +5 for ≥3 signals, +5 more for ≥6
- Verified: market_score 65→75 after backfill, tier upgraded to COMPETITIVE

### [auction] Coaching panel on vehicle profile
- New: `AuctionReadinessPanel.tsx` — composite score, tier badge, 6 dimension bars, MVPS status, coaching actions list
- Wired into `WorkspaceContent.tsx` below VehicleScoresWidget
- Design system compliant: Arial, ALL CAPS 8-9px, 2px borders, zero radius

### [auction] Comment re-extraction for ending BaT auctions
- `sync-live-auctions` now triggers `extract-auction-comments` for BaT auctions ending within 6 hours
- Fire-and-forget, capped at 10 per sync cycle
- Deployed both edge functions

### 2026-03-24
### [valuation] Bonhams valuation coverage fix — 7.1% → 35.8% high-confidence
- Root cause: Bonhams model strings are hyper-specific (chassis nos, accented chars, registration data)
  - Model uniqueness ratio 0.917 (vs 0.115 for Mecum) — comp matching found ~0 cross-source comps
  - e.g., "911 2.0 racing coupe chassis no. 9110101449 engine no. 3180044" matches nothing else
- Fix: Multi-tier comp matching in `compute-vehicle-valuation`:
  - Tier 1: canonical_models aliases (3,454 canonical models with aliases)
  - Tier 2: Exact model string (original logic)
  - Tier 3: Normalized model (strip chassis/VIN/accents)
  - Tier 4: Core model tokens (first 1-3 significant words)
  - Tier 5: Make-only fallback with wider year range
- Added normalizeModelForComps() and extractCoreModel() functions
- Updated confidence scoring for new match tiers + confidence interval widening
- Deployed compute-vehicle-valuation, batch-extracted 4,379/4,450 vehicles
- Also added "Sold for" price fallback to batch-extract-snapshots Bonhams parser
- Results: high_conf 323→1,628 (+5x), no_estimate 578→78, avg_confidence 55→64

### 2026-03-25
### [data] BaT gap discovery analysis + queue health fix
- BaT total catalog confirmed: 234,943 listings via API (234,943 items_total from listings-filter endpoint)
- Our actual unique clean URLs: 165,339 (previous 204K count was inflated by 39K comment fragment URLs in queue)
- TRUE discovery gap: ~69,600 listings (mostly pre-2024, older than what API can paginate to)
- API limitation found: BaT's listings-filter API has a hard 275-page limit (~9,900 items max per unfiltered query)
  - Filter params (era, make, keyword_pages) are silently ignored by the API
  - HTML results pages return identical content regardless of ?page= param (Knockout.js dynamic loading only)
  - Only way to reach deeper results: Playwright "Show More" clicking through all 6,500+ pages
- Queue reconciliation: marked 96,418 bat_extraction_queue entries as 'complete' (vehicles already existed)
- Queue cleanup: marked 39,213 comment fragment URLs (#comment-XXXXX) as 'failed' (not actual listing URLs)
- Queue status after cleanup: 30,528 genuinely pending (8,251 with snapshots, 22,277 need fetching)
- Created scripts/bat-gap-discovery.mjs — API-based discovery + DB comparison + reconciliation
- Created scripts/bat-deep-discovery.mjs — Playwright-based deep discovery to find the remaining ~69K
- Queue processor bottleneck: process-bat-extraction-queue forces batchSize=1 despite cron sending 15. At 1/5min = 288/day, 30K queue would take 104 days.

### [data] Classic Driver sitemap intake — 54,428 European collector car listings
- Classic Driver = largest European collector car marketplace, zero previous coverage
- Sitemap: 31 pages, 54,890 total car URLs extracted from classicdriver.com/sitemap.xml
- URL pattern: /en/car/MAKE/MODEL/YEAR/ID — parsed make/model/year directly from URLs
- Registered as observation_source (slug: classic-driver, category: marketplace, trust: 0.80)
- Also registered in scrape_sources (FK requirement for import_queue)
- Queued 54,428 URLs into import_queue (54,419 with Y/M/M + 9 ID-only)
- Parse quality: 99.4% have make, 98.9% have model, 99.9% valid year range
- Top makes: Porsche (5,288), Mercedes-Benz (5,211), Ferrari (4,213), Jaguar (3,573), Ford (2,630)
- Year range: 1886-2025, heaviest in 1960s (11,621) and 1950s (7,268)
- 1,084 unique makes, 154 unique years — massive European market diversity
- All queued at priority 5 (bulk sitemap) for extraction via existing pipeline

### [data] ClassicCars.com sitemap discovery + 35K listing queue
- Researched ClassicCars.com: Cloudflare-protected but browser UA bypasses; Azure Blob sitemaps unprotected
- Discovered sitemap_index.xml with 71 listing sitemaps at ccpublic.blob.core.windows.net
- Parsed all 71 sitemaps: 35,070 unique listing URLs with 1,421,309 embedded images
- URL format: /listings/view/{id}/{year}-{make}-{model}-for-sale-in-{city}-{state}-{zip}
- Listing pages contain JSON-LD schema.org data (@type: car) with VIN, price, mileage, colors, description
- Created scrape_source: ClassicCars.com (e348ec0c-34e5-4bc0-8d26-78aeaba5443e)
- Queued 35,070 URLs into import_queue: 33,900 pending, 1,170 auto-skipped (matched existing vehicles)
- Priority distribution: 17,909 newest (P1), 16,544 recent (P2), 617 older (P3-P5)
- No RSS feed found; no public API discovered; search page returns HTML only
- Observation source already existed: classiccars-com (495e3f21-973c-43b1-9580-c214c8b7cb91)
- Also found: 550 dealer pages, 21 auction pages in separate sitemaps

### [data] Deep extraction of 109 skeleton vehicles across 11 major sources
- **Goal:** Founder wanted quality samples from every source — fully extracted with description, VIN, price, images
- **Problem:** OpenAI quota exhausted, edge function `extract-vehicle-data-ai` LLM fallback chain broken (not falling to Anthropic/Google despite code)
- **Solution:** Built local extraction pipeline: Firecrawl scrape → xAI/Grok AI extraction → direct PostgREST DB update
- **Results:** 75/109 vehicles enriched with real data in the database:
  - **bat**: 10/10 — Excellent. All have description, price, mileage, color, transmission, engine. 8/10 VIN.
  - **barrett-jackson**: 10/10 — Excellent. 8/10 VIN, 6/10 price (upcoming auctions), all have descriptions.
  - **pcarmarket**: 10/10 — Excellent. All have description, price, full specs. 4/10 VIN.
  - **bonhams**: 10/10 — Good. All have descriptions, 8/10 price (CHF/GBP currencies), 10/10 VIN from chassis numbers.
  - **gooding**: 9/10 — Good. 7/10 price, descriptions, rare pre-war vehicles. 1 xAI parse failure.
  - **jamesedition**: 9/10 — Good. 10/10 VIN, 9/10 mileage/transmission. Low descriptions (dealer site). 1 scrape fail.
  - **mecum**: 6/9 — Medium. 3 scrape failures (Mecum blocks). 8/9 VIN for those scraped. No prices (auctions).
  - **craigslist**: 6/10 — Medium. 4 scrape failures (listings expired). 6/10 with description + price.
  - **collecting_cars**: 4/10 — Low. Site scraped OK but xAI had trouble with Collecting Cars format. Some prices found.
  - **cars_and_bids**: 1/10 — Low. 6 scrape failures (Cloudflare/timeouts). Only 1 fully extracted.
  - **rm-sothebys**: 0/10 — Failed. Pages scrape OK but contain mostly navigation/catalog UI, not listing content.
- **Key finding:** `extract-vehicle-data-ai` edge function needs fix — all 3 LLM providers fail (OpenAI quota, Anthropic key issue, Google key as GEMINI_API_KEY not GOOGLE_AI_API_KEY). The Supabase secrets have the keys but the deployed code may not resolve them correctly.
- **Showcase vehicles with full data:**
  - 2023 Corvette Z06: $135,500, 4 miles, VIN, full description, all specs
  - 2020 Mercedes-AMG GT R Roadster: $124,500, 19K miles, VIN, full description
  - 2025 Lotus Emira (BJ): $129,800, VIN, 320 miles, all specs
  - 1997 Porsche 993 Turbo S (PCM): $575,000, 21K miles, VIN, full description
  - 1936 Harley-Davidson E Knucklehead (Gooding): $93,500, all specs

### [docs] Extraction Playbook — The Book of What Works (1,688 lines)
- `docs/library/technical/extraction-playbook.md` — comprehensive extraction reference
- 16 extraction methods documented with cards (status, throughput, cost, failure modes, LLM config)
- 14 documented failures with root cause, fix, prevention rules
- LLM configuration guide: 9 models, cost table, API endpoints, JSON quirks, full prompt inventory
- 5 architecture patterns (Snapshot First, API Discovery, Validate Before Insert, Persistent Connections, Source-Agnostic Pipeline)
- 5 copy-paste runbooks (condition extraction, new source setup, backfill, health check, deploy)
- Current state dashboard (745K vehicles, 3.78M observations, 25 active crons, blockers)
- 11 source-specific technical notes (BaT, C&B, Mecum, FB, Hagerty, BJ, Bonhams, RM, PCarMarket, ClassicCars, Classic Driver)
- 3 appendices: file index (30 key files), 12 anti-patterns, confidence/trust scoring system
- Sources: 6 research agents analyzed 43 edge functions, full DONE.md history, live DB metrics, session logs, all LLM prompts

### [docs] Extraction Playbook v2 — post-critique revision (2,102 lines)
- 4-agent critique simulation: fresh agent, security reviewer, data engineer, tech writer
- SECURITY FIX: removed plaintext DB password (was in health check runbook)
- SECURITY FIX: `--no-verify-jwt` deployment template replaced with JWT-by-default + warning
- Added Section 0: Key Concepts (execution model, schema glossary, accuracy definition, batch size rules, terminology)
- Added 2 new runbooks: Diagnose Queue Failures, Check Cron Status
- Added Appendix D: Known Architectural Limitations (idempotency, backpressure, monitoring, rollback, connection pool)
- Standardized all 16 method card headers (LLM, THROUGHPUT fields)
- Added cross-references from runbooks to related failures
- Clarified local-vs-cloud execution boundary for LLM routing
- Documented `continue: true` parameter behavior
- Explained dual table system (observation_sources vs scrape_sources)

### [docs] The Extraction Handbook — expanded from playbook to textbook (2,745 lines)
- Renamed from "Extraction Playbook" to "The Extraction Handbook" — complete institutional knowledge
- Added Chapter 1: History — 16 eras of extraction from Feb 2025 to present, every pivot, every failure
- Added Chapter 2: Repeated Mistakes — 12 documented patterns with occurrence tallies (7 still recurring)
  - BaT extractor rewritten 7+ times, LLM credits exhausted 6+ times, batch timeouts 12+ incidents
  - Auth redirect bug still affects 36/40 extractors
- Added Chapter 10: Facebook Marketplace — complete status, the SLC square body use case, 6 fixes needed (~8 hrs)
  - 33K FB vehicles, scraper running 4x/day, but location doesn't propagate and no proximity search exists
- Added Chapter 11: Stalled Initiatives — 9 extraction efforts audited
  - 4 ACTIVE (comments, valuations, RSS, FB), 4 STALLED (ConceptCarz, forums, OCR, iPhoto), 1 ABANDONED (tools)
- Reordered chapters into 4 parts: Context (0-2), Methods (3-5), Operations (6-8), Sources (9-11) + 4 appendices
- Total: 12 chapters, 4 appendices, 130 subsections, 17 major sections

### [docs] The Extraction Handbook v3 — full textbook (2,998 lines)
- Added Chapter 12: Prompt Evolution — 8 eras from 12.6% Chevy-truck-specific template to testimony-grade forensics
  - Documented the catastrophic hallucination discovery: reference injection caused 66% fabrication on Porsche
  - Key lesson: "Reference library = decoder ring, NOT shopping list"
  - Arc: generic ($0.50/vehicle, 12.6%) → open-ended ($0.05) → regex ($0, 68%) → testimony (citation-verified)
- Added Chapter 13: Graduation Path — 4 graduation levels with measurable criteria
  - Current state: 814K vehicles, 97% identity, 30% everything else
  - Graduation 1 (Claims Exhausted): 3-6 months, all source material extracted with provenance
  - Top ROI: re-extract Mecum+BJ (244K vehicles), decompose descriptions (286K), provenance backfill (363K)
  - Honest answer: extraction is not close to done, but the path is clear
- Restructured into 5 parts: Context, Methods, Operations, Sources, The Big Picture
- 14 chapters + 4 appendices, 18 major sections total

### [extraction] 4 high-ROI actions from Extraction Handbook
- **BaT queue cleanup:** 43,406 terminal failures reclassified to `skipped` (comment URLs 89%, non-vehicles 9.5%, garbled URLs). Failed items: 44K → 590.
- **Proximity search RPC:** `find_vehicles_near()` deployed — Haversine distance, mile-based radius, bounding box pre-filter, optional year/make/source filters, GPS index added. **35 square body trucks within 250mi of SLC** (was 0 findable results). Replaces broken `find_vehicles_near_gps` (100m bounding box, wrong search_path).
- **Barrett-Jackson VIN backfill:** Extracted chassis numbers from 20K+ conceptcarz:// URLs + 1.5K from import_queue raw_data. VIN any-length: 31.7% → 31.8% (most short chassis numbers hit dupe constraints). Snapshot queue fully processed (43K complete). BJ Strapi API now behind Cloudflare.
- **Mecum snapshot re-extraction:** Fixed CRITICAL bug in `repopulate_snapshot_queue()` — `AND s.html IS NOT NULL` blocked ALL platforms since 100% of 440K+ snapshots use `html_storage_path`. Added URL normalization (9 match patterns). Batch_size doubled to 100. 29K queue items draining at 3,600/hr. Price: 44.4% → 44.9%, mileage: 28.3% → 28.8%, engine +12.2pp.

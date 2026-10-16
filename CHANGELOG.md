# Changelog

All notable changes to npiradar are documented here.
The format is based on [Keep a Changelog](https://keepachangelog.com/en/1.1.0/).

## [Unreleased]

### Fixed — October 2026 NPPES file wrote the text "NULL" as license state (2026-10-16)

**Why:** `live.providers.license_state` held the literal string `'NULL'` for 3,057,162 providers after
the October V2 load (September: 0; no other column affected). `clean()` keeps any non-empty text, so
the diff logged `NULL → 'NULL'` as a license change: 3,044,913 of the 3,193,461 rows for release
2026-10-12 were this. Nothing user-facing: the NPI page shows the state only next to a license number.

- `pipeline/lib/provider.ts`: `license_state` goes through `stateCode()`, which keeps only a 2-letter
  code (the only non-matching value in the live data was `'NULL'`). `npiradar-refresh` rebuilt.
- Data repaired in one guarded transaction: `license_state = NULL` for the 3,057,162 rows; in
  `provider_changes` for 2026-10-12, a trailing `" NULL"` stripped from license values, 336 real changes
  kept (stripped), and 3,026,410 rows deleted where old and new then matched. Release 2026-10-12 is
  now 167,051 changes, 18,503 of them license. Pre-repair copies: the 2026-10-16T18:06 backup (local
  and R2).

### Fixed — /open-payments took ~7 s on the first request after every restart (2026-10-07)

`lib/insights.ts` cached the national Open Payments / OIG stats for a day per process, so the first
visitor after a deploy, restart or daily expiry waited for the ~1M-row scan (7.0 s; OIG page 0.33 s).
- Stale-while-revalidate: once cached, an expired value is served while one background recompute
  replaces it; concurrent first requests share one computation.
- `instrumentation.ts` warms both at server start (~7 s in the background; "insights: warmed" in the log).
  The cache lives on `globalThis` because Next bundles instrumentation separately from the pages, so a
  module-level Map warmed at startup was invisible to them (first try: still 6 s).
- The Dockerfile copies named files only, so `instrumentation.ts` had to be added there (and to
  `tsconfig.json`'s include, or `tsc` never checks it).
- First request after a deploy: `/open-payments` 7.0 s → 0.15 s, `/oig-exclusion-check` 0.33 → 0.03 s.

### Added — Care Compare background, groups and affiliations; Medicare revalidation; license verify links (2026-10-07)

**Why:** the last three items of the data fold-in plan. Care Compare is CMS's richest public file per
clinician and none of it is on the NPI registry; `medicare provider lookup` is 3,600/mo, `pecos lookup`
4,400/mo, `medicare revalidation lookup` 880/mo, license lookups 2,400-49,500/mo (US).

**What changed:**
- `pipeline/lib/cms-csv.ts`: the stream → stage → `<table>_next` → swap → `dataset_loads` loader, moved out
  of `medicare.ts` so `carecompare.ts` shares it. A dataset may now build several tables from one file.
  Output indexes are named `<table>_key`.
- `medicare.ts` + **Revalidation Due Date List** → `public.medicare_revalidation` (2,961,404 enrollments,
  2.46M NPIs). Only ~10% carry a date; the page says "No due date set by CMS yet" for the rest, and marks
  a date that has passed. API `medicare.revalidation`; bulk `medicareRevalidationDue` (earliest date set).
- `pipeline/carecompare.ts` (provider-data catalog): `cc_clinicians` (1,627,468 NPIs: medical school,
  graduation year, secondary specialties, telehealth, Medicare assignment), `cc_groups` (1,767,885
  clinician × group rows), `cc_affiliations` (2,253,990) and `cc_hospitals` (5,419, to name the 85% of
  affiliations that are hospitals; 99% match by CCN). 649 MB, ~3 min. CMS writes "OTHER" for ~60% of
  medical schools; stored as null. `/npi/[npi]` "Medicare Care Compare" section; API `careCompare`.
- `refresh-server.ts`: `runCmsLoader` runs `medicare.ts` and `carecompare.ts` on the 6-hourly check.
- License: `lib/license.ts` links physicians to DocInfo (FSMB) and nurses (RN, LPN/LVN, NP, CNS, CRNA,
  midwife) to Nursys; everyone else is told to verify with their state's board (no single source exists).
  Shown next to the license number; API `licenseVerification`. Nursys 403s server requests, so the link
  goes to its home page rather than a QuickConfirm deep link that couldn't be checked.

### Fixed — Slow city, specialty and home pages (2026-10-07)

**Why:** these pages render per request, and three queries scaled with the size of the facet. Houston's
city page took 1.2-1.3 s; specialty pages and big specialty×city pages ~0.45 s.
- Listing: `col = ANY(keys) ORDER BY last_name …` read and sorted every provider in the facet (Houston:
  87k rows, 773 ms) because no index matched the sort.
- City "Industry payments and exclusions": joined every provider in the facet to `op_npi_year` on each
  request, twice (~1-1.5 s for a large city).

**What changed:**
- `facets.sql`: `idx_providers_city_name` (state, city, last_name, org_name, npi) and `idx_providers_tax_name`
  (taxonomy, last_name, org_name, npi), both partial on active rows (~600 MB each). `lib/facets.ts`
  `listByKeys` scans each raw city / code in index order for just offset+limit rows and merges: 773 → 5 ms.
- `facets.sql` §5: `mv_facet_insights`, one row per city and per specialty×city with a paid or excluded
  provider (paid, total, excluded, top 5 as JSON). ~20 s to build, ~100 MB, 0.5 ms to read. Rebuilt with
  each NPPES load; `openpayments.ts` and `leie.ts` refresh it (CONCURRENTLY) after a load that changed
  data (`pipeline/lib/insights.ts`). Skipped on a database without those tables.
- Home page, `llms.txt` and the sitemap's data-version stamp each ran a count(*) / max() over ~9.8M rows
  (~0.5 s) on the first request after every restart; the home page's p99 was 682 ms. Now one precomputed
  row, `mv_provider_totals` (`facets.sql` §4b): cold home 138 ms, cold `sitemap.xml` 81 ms.
- Built on the live schema by hand. Measured in the container: Houston 1,229 → 80 ms, Stamford 435 → 35 ms,
  `/specialty/behavior-technician` 469 → 46 ms, family medicine in Houston 470 → 49 ms. Rendered text is
  identical before and after on all 7 sampled pages (lists, page 10, insights).

### Fixed — Docs claimed provider pages were ISR-cached for 30 days; they never were (2026-10-07)

Provider, specialty and city pages (and their OG images) set `revalidate` but have no
`generateStaticParams`, and Next 15 doesn't ISR a dynamic route without one: they render on every
request (`cache-control: no-store`). Measured: ~21 ms p50 / 64 ms p99 at ~22k provider hits/h. Kept that
way on purpose: caching ~9M pages would write each to disk as it's crawled, to save ~20 ms. Data loads
therefore show on the next request with no purge. Corrected in `ARCHITECTURE.md` §4 (the canonical
note), STATUS, README, SEO, IMPLEMENTATION, `pipeline/README.md`, `REFRESH.md` and the code comments.

### Added — Medicare enrollment, order & referral eligibility, opt-out (2026-10-07)

**Why:** "can this NPI bill or order for Medicare?" is a check billing teams run on every claim, and CMS
spreads the answer over three files that its NPI registry doesn't show. `pecos lookup` is 4,400/mo (US).
Together with the OIG flag, a provider page now answers it.

**What changed:**
- `pipeline/medicare.ts` loads three data.cms.gov files, each the newest CSV in the catalog
  (`data.json`; versions are separate entries titled "<title> : YYYY-MM-DD"):
  `public.medicare_enrollment` (Public Provider Enrollment, quarterly, one row per enrollment),
  `public.medicare_order_referring` (Order and Referring, ~twice weekly, one row per NPI) and
  `public.medicare_opt_out` (Opt Out Affidavits, monthly, one row per affidavit). Each streams into a stage
  table, is built as `<table>_next`, and swapped in one transaction. A dataset whose URL is already loaded
  is skipped (`dataset_loads.source`); one failing doesn't block the others; a file under its row floor is
  refused. The tables are LOGGED on purpose: an UNLOGGED table comes back empty after a crash, and every
  page would then say "not enrolled".
- History: `medicare_enrolled` / `medicare_unenrolled`, `medicare_opted_out` / `medicare_opt_out_ended`,
  and `medicare_ordering` (old → new program list). Not recorded on a dataset's first load.
- The opt-out file keeps affidavits whose end date has passed (3,164 of 57,780 in Aug 2026), so "opted
  out" means an affidavit with `end_date >= today`; ended ones show as past opt-outs. The enrollment file
  isn't UTF-8, so it's read as Latin-1.
- `refresh-server.ts` runs it on the 6-hourly check, after LEIE, skipping while an NPPES refresh runs.
- `/npi/[npi]`: a "Medicare" section (enrollment, order & refer, opt-out, each "as of" its load date,
  with a pointer to PECOS). An absent record is stated only once the files are loaded; order & refer
  and opt-out are shown for individuals only. A current opt-out also leads the meta description.
- `GET /api/npi/{npi}`: `medicare` (enrollments, `orderReferring` per program or null, opt-out
  affidavits, `asOf`). Bulk `POST /api/npi` and `/tools/bulk-lookup` (table + CSV) carry
  `medicareEnrolled`, `medicareOptedOut`, `medicareOrderRefer`.
- First load: 2,978,925 enrollments / 2,541,258 NPIs; 2,056,486 order & referring NPIs; 57,624 opt-out
  affidavits / 57,015 NPIs.

### Added — Taxonomy codes on specialty pages (2026-10-07)

**Why:** `taxonomy code lookup` is 1,900/mo (US). Every code already had a specialty page, but the code
itself was absent from its title, heading and description, so the page couldn't rank for it, and a
typed code didn't resolve.

**What changed:**
- `taxonomy.definition`: NUCC's definition, which the loader used to drop. NUCC's placeholder "Definition
  to come..." (216 codes) is stored as null. The live schema was backfilled by hand from
  `nucc_taxonomy_251.csv` (657 of 883 codes have one); `load.ts` writes it from the next load on.
- `/specialty/[slug]`: code in the title and description, a "Taxonomy code" row, and the NUCC
  definition on page 1. `/specialty/207Q00000X` (any case) 308s to the specialty page; `/search?q=<code>`
  redirects there too.
- `/specialty` lists each specialty's code; the provider page's taxonomy code links to its specialty.

### Added — CMS Open Payments: industry payments per clinician (2026-10-07)

**Why:** what drug and device makers paid a clinician is public, searched for, and hard to read on
CMS's own site. It is the largest block of per-NPI content the NPI registry doesn't have.

**What changed:**
- `pipeline/openpayments.ts` finds each program year's general-payments CSV (~9 GB, ~15M rows) through
  CMS's DKAN catalog, streams 6 columns into an UNLOGGED `public.op_stage`, aggregates per NPI into
  `op_npi_year` (total, payments, companies), `op_npi_company` (top 10) and `op_npi_nature` (by payment
  type), swaps that year's rows in one transaction, then drops the stage and deletes the download.
  Keeps the latest 3 program years. A year whose catalog URL is already loaded is skipped
  (`dataset_loads.source`), so a check is one catalog fetch. CMS republishes years with corrections;
  a new URL reloads that year.
- Aggregation is serial at `work_mem=64MB`, for the same /dev/shm reason as the NPPES diff.
- `refresh-server.ts` runs it on the 6-hourly check, but never while an NPPES refresh is running.
- `/npi/[npi]`: "Payments from drug and device companies" (by year, top companies and payment types for
  the latest year, with "reporting a payment does not imply wrongdoing"). `GET /api/npi/{npi}`:
  `openPayments`.
- If a load fails, the download and `op_stage` stay for the retry; the next run drops the stage first
  and resumes the download.
- First load, program year 2025: 16,089,033 rows with an NPI → 1,020,608 NPIs, $2.89B. 2024 and 2023 were
  loaded by the scheduler right after.

### Added — HHS OIG exclusion flags (LEIE) (2026-10-07)

**Why:** OIG's exclusion list bars people and entities from federal health programs, but CMS's NPI
registry doesn't show it: 7,724 of the 8,700 listed NPIs are still active NPIs that look clean there.
Screening for exclusions is a monthly compliance job for billing and credentialing teams.

**What changed:**
- `pipeline/leie.ts` downloads OIG's `UPDATED.csv` (~84k rows), keeps rows with a real NPI (8,881 / 8,700
  NPIs) into `public.oig_exclusions`, and records `oig_excluded` / `oig_reinstated` in `provider_changes`
  (not on the first load, when everyone would read as new). Skips when the file's sha256 is unchanged
  (`public.dataset_loads`); refuses a file under 50k rows; purges the ISR cache when the list changed.
- **NPI match only, never by name.** A wrong exclusion flag is the one error this can't afford.
- `refresh-server.ts` runs it on the same 6-hourly check (inline; it takes seconds).
- `/npi/[npi]`: banner citing the OIG section and date, "as of" the load date, and a link to OIG's own
  search to confirm. `GET /api/npi/{npi}`: `oigExcluded`, `oigExclusions[]`, `oigListAsOf`, `oigSource`.
  Bulk `POST /api/npi` and `/tools/bulk-lookup` (table + CSV) carry `oigExcluded` and `deactivated`.
- `pipeline/lib/changes.ts` holds the `provider_changes` DDL shared by `load.ts` and `leie.ts`.

### Added — Registry history: month-over-month change log (2026-10-07)

**Why:** NPPES publishes only each provider's current record. History exists only if someone keeps it,
and it can't be backfilled, so every load we skip is lost for good. It is the one thing on a provider
page that CMS's own registry can't show.

**What changed:**
- `load.ts --diff <schema>` compares the freshly built schema with `live` and writes
  `public.provider_changes (release, npi, change, old_value, new_value)`. That table sits outside the swapped
  schemas, so it accumulates. Change types: `added`, `removed`, `deactivated`, `reactivated`,
  `practice_address`, `practice_phone`, `primary_taxonomy`, `name`, `credential`, `license`.
- `load-parallel.ts` runs it right before `--swap`. A failed diff is logged and never blocks the swap.
- `release` = the new file's `max(last_update_date)`. A same-release re-run is skipped, so it can't wipe
  that month's diff. Deactivated records arrive with fields blanked, so a (de)activation is recorded alone.
- Runs serially at `work_mem=64MB` (~25s on 9.8M rows). A parallel hash join at 256MB/worker overflowed
  postgres's 1GB `/dev/shm`.
- `/npi/[npi]` shows a "Registry history" section; `GET /api/npi/{npi}` adds `changes`.
- **First diff: the October 2026 release** (September vs September gave 0 differences, a sanity check).

### Changed — Real data-vintage label, 6-hourly refresh check, NPPES side files (2026-10-07)

**Why:** The site said "NPPES — May 2026 release" while serving the September file. `DATA_VINTAGE` was a
hand-bumped constant, missed for four loads, so Google and `llms.txt` readers saw a site 5 months stale.
The refresh also ran on the 1st while CMS posts around the second weekend, so data was 3–7 weeks old.
And every page was a strict subset of CMS's own registry: the loader discarded the three side files.

**What changed:**
- `dataVintage()` (`lib/facets.ts`) reads the last successful `refresh_runs.source_file` →
  "NPPES — September 2026 release". Used by the footer, the homepage Dataset JSON-LD, `llms.txt`, `/nppes`,
  `/npi-api`, `/tools/bulk-lookup`. At build (no DB) it falls back to "NPPES monthly release", so the
  static pages now `revalidate` daily.
- `refresh-server.ts` runs its own check every 6h (plus 60s after boot). No-op unless CMS has a newer file.
- `fetch-monthly.sh` also extracts `othername_`, `pl_` and `endpoint_pfile_*.csv`; `load.ts --side` COPYs them
  (in parallel with the provider shards) into `provider_other_names` (853k), `provider_locations`
  (1.19M, 776k NPIs) and `provider_endpoints` (598k: Direct, CONNECT, SOAP, FHIR…). Indexed on npi, LOGGED.
- `/npi/[npi]` shows Other names / Other practice locations / Electronic endpoints (first 25 of each).
  `GET /api/npi/{npi}` adds `otherNames`, `secondaryLocations`, `endpoints` (all rows) and their counts.
  Bulk `POST /api/npi` is unchanged.
- Homepage Dataset `creator` `GovernmentOrganization` → `Organization` (GSC: `Invalid object type for field "creator"`).

### Changed — Index-eligibility cut: 307k → ≈10.7k submitted URLs (2026-09-24)

**Why:** The 2026-09-24 search audit (`~/scripts/seo/audits/npiradar.md`) found 1 of 156 ranking pages
indexed (3/210 on 07-27), and 20 of 20 sampled sitemap URLs never discovered. Googlebot has dropped to about 40
requests a day. The tools pages and `/specialty` were still "URL is unknown to Google". Nearly half of all city
pages (17,734 of 37,850) had fewer than 5 providers, many of them NPPES address typos (`/in/az/cullman`,
`/in/mo/crystal-cty`). Google was declining the corpus as scaled thin content.

**What changed:**
- `INDEXABLE_MIN` 5 → **200** (specialty×city); new `CITY_INDEXABLE_MIN = 250` wired into the city page's
  robots meta and `cities.xml`. Below threshold a page is `noindex, follow`: still crawlable, linked, and
  unchanged for users.
- `SITEMAP_RULES_VERSION` floor on `dataVersion()`. Without it the 304 short-circuit (below) would hide the
  cut: Google's `If-Modified-Since` still matched the data version, so it would never re-fetch the smaller
  sitemaps. Bump it whenever inclusion rules change.
- New `/nppes` explainer and `/npi-api` docs page (in `pages.xml`, nav, home, `llms.txt`). Bulk-lookup is
  refocused on bulk and points to `/npi-api` instead of carrying the full API docs.

### Added — Public API: bulk + search endpoints with first-class rate limiting (2026-07-13)

**Why:** GSC surfaced real demand for programmatic access (e.g. *"ai tool that pulls bulk practice
locations based on npi free nppes"*), but the only endpoint resolved a single known NPI — no batch,
no discovery, and no app-level rate limiting beyond Traefik's coarse edge limit.

**What changed:**
- `POST /api/npi` — bulk lookup (≤100 NPIs) in one `WHERE npi = ANY(...)` round-trip
  (`lib/provider.ts → getProviders`). `app/tools/bulk-lookup/bulk.tsx` now makes one POST instead of
  a 100-way per-NPI client fan-out.
- `GET /api/search` — filtered discovery by `name` / `specialty` / `state` / `city`
  (`lib/facets.ts → searchProvidersApi`), with guardrails that keep every query on an index.
- **Rate limiting as a shared primitive** — Redis-backed, cost-weighted, per-IP (`lib/redis.ts`,
  `lib/ratelimit.ts`, `lib/api.ts`), applied to all three public endpoints. One token budget
  (default 600/min/IP); single = 1, bulk = N NPIs, search = 10. Emits `X-RateLimit-*` + `Retry-After`.
  Fails open if Redis is unreachable.
- Deps/infra: `ioredis` added (+ `serverExternalPackages`); `REDIS_URL=redis://redis:6379` in the
  `projects/npiradar` compose.

**Operational detail + verification commands:** see `OPERATIONS.md`.

### Changed — Sitemap crawl-budget efficiency (2026-06-14)

**Why:** A Search Console diagnosis (scripts in `~/project-research/gsc-diagnose.cjs`,
`gsc-inspect.cjs`) found indexation was crawl-starved, not quality-rejected. A random sample of
14 provider pages all came back *"URL is unknown to Google — never crawled,"* while the crawl-stats
export showed Googlebot spending **~84% of its budget on "refresh"** and **~79% on "other file
type."** Those non-HTML refresh hits are the sitemap XML files: every child sitemap was
`force-dynamic` with no `Last-Modified` and no `lastmod` on the index entries, so Google
re-downloaded the full set on every pass instead of being told they were unchanged.

NPPES data only changes with the monthly load, so sitemaps only change monthly. We now say so.

**What changed:**

- `lib/sitemap.ts`
  - `xmlResponse(xml, lastmod?)` now sets a `Last-Modified` validator when given a data version.
  - Added `notModified(req, lastmod)` and `notModifiedResponse(lastmod)` to answer conditional
    re-crawls (`If-Modified-Since`) with a cheap **304** instead of a full XML re-download.
- `lib/facets.ts`
  - Added `dataVersion()` — `max(last_update_date)` as a `YYYY-MM-DD` stamp, cached per-instance for
    a day (the one uncached `max()` over ~9M rows runs at most once per instance per day). Fails open
    to today's date so a DB blip triggers a re-crawl rather than serving a stale validator.
- Sitemap routes now stamp `Last-Modified` and short-circuit unchanged re-crawls to 304:
  - `app/sitemap.xml/route.ts` (index) — also adds `<lastmod>` to every child `<sitemap>` entry, so
    Google can skip child sitemaps it already has at that version.
  - `app/sitemaps/providers/[file]/route.ts`
  - `app/sitemaps/specialty-cities/[file]/route.ts`
  - `app/sitemaps/cities.xml/route.ts`
  - `app/sitemaps/specialties.xml/route.ts`
  - The provider/specialty-city routes 304 **before** querying the DB; safe because the page set can
    only change when `dataVersion` advances, so a 304 never masks a page that has since 404'd within
    the same data version.

**Expected effect:** Googlebot stops re-downloading unchanged sitemaps every pass, redirecting the
recovering crawl budget toward actual provider HTML pages — faster discovery/indexation of the
long tail. After each monthly load `dataVersion` advances and Google re-fetches all sitemaps once,
which is correct (the data did change).

**Verification:** `tsc --noEmit` clean. (No local eslint binary; repo exposes only a `build` script.)

### Investigated but intentionally not changed

- **Internal linking** — already solid: provider pages link to their specialty/city/specialty×city
  hubs (`LinkChips`), and hubs list providers with pagination (`ProviderList` + `Pager`). No change
  needed; the discovery gap was crawl budget, not the link graph.
- **`robots.txt` resilience** — served from `public/` by the Node app, so it goes down during an
  outage (GSC showed ~0.64% "robots.txt unavailable", which pauses crawl). Serving it from Traefik
  independent of the app would make crawl pauses impossible. Deferred — infra change, and reliability
  is already recovering. Tracked as a follow-up.

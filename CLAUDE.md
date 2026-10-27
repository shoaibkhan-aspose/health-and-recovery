# Site Health & Recovery Agents

Domain-agnostic agents that audit a web property, report what is broken, not optimized, incorrect or improvable, and (in a later phase) fix it. Pilot tenant: **aspose.app** and all of its subdomains.

**Goal:** grow organic traffic from classic search and AI answer engines (SEO, GEO, AEO, AIO).

**Owner:** SK. This file is the master brief. A copy lives in the claude.ai Project "aspose.app Health Recovery Agents"; Claude Code in VS Code cannot write to it, so when this file changes meaningfully, tell SK so he can refresh the Project copy.

**Keep this file current:** when a decision is made, a fact is confirmed or a build step finishes, update the relevant section (Status, Seed findings, Open items) in the same session. New issues found by hand go into `tenants/aspose.app.seed-findings.yaml`, never only into prose.

## Start here (session handoff, 2026-10-27)

**State:** Phase 1 (audit only). Four tenants: **aspose.app** (11 hosts, 29 product families), **conholdate.cloud**, **aspose.cloud** and **groupdocs.cloud** (the three .cloud tenants have only their blog for now; more hosts later). Built and live: discovery, crawl auditor (33 checks), speed auditor (PageSpeed Insights), AI-readiness auditor, text check (LLM), **link check** (repo-based, 6 checks, new 2026-10-22), findings store, Prioritizer, family and host scorecards (health A-F), the reports with archives, host pages, a shared fix guide page and a landing page. Everything is committed and pushed to `github` and `origin` (GitLab); working tree clean.

**Commit identity:** always `Shoaib Khan <shoaib.khan@aspose.com>`, set in this repo's `.git/config` (something on the Mac switches the global `~/.gitconfig` to SK's personal gmail). Check `git log -1 --format='%ae %ce'` after every commit. History was rewritten on 2026-10-22 so all commits carry this address (see Working rules); every commit id from before that day changed.

**Site layout (Pages, https://shoaibkhan-aspose.github.io/health-and-recovery/):**
- `/` landing page: each property with its open findings, archive link and host links.
- `/<tenant>/` property report, `/<tenant>/archive/` its frozen snapshots (snapshots stay per property). With the Overview layout (`report.manager_view`; today aspose.cloud) the property page shows one **host card** per host (health, clicks and impressions with changes, open issues, change since last run, area scores with broken badges, link to the host page; lowest health first) and **Top actions required** (top 5 across hosts, linking to `/<host>/#f-<id>`); its Details are hidden on the live page (they live on the host pages) but kept in snapshots. SK first chose a redirect for single-host properties, then (2026-10-27) the same property page for every property, as aspose.app will use it.
- `/<host>/` one page per host (flat URLs, SK's choice): the property report filtered to that host, scores identical (`build_report --host`, `focus_host`). `build_site.site_hosts` stops the build if a host name equals a tenant or a site folder (`fix-guide`, `method`, `archive`). Apex domains redirect to www (aspose.app, aspose.com), so no clash today.
- `/fix-guide/` one shared fix guide (all checks, anchors `#g-<check>`, open findings per report). Published reports have no Fix guide section; every "How to fix" link goes there. Local builds keep the full table.
- `/method/` one shared "How this audit works" page (SK, 2026-10-26; anchors `#method-health`, `#method-score`). Source `scripts/templates/method.html`, used by `build_site.method_page` and inlined by `build_report` for local builds; published reports and new snapshots (`--method-url`, `SNAPSHOT_METHOD_URL`) have no method section and link there. Older snapshots keep their own section.
- Header: Property and Host dropdowns (switching keeps the #section), "All reports" link. Local pages and snapshots have no switches.
- Old links (`/aspose-app-health-and-recovery/...`, before the repo rename) work through the redirect repo `shoaibkhan-aspose/aspose-app-health-and-recovery` (local clone `/Users/Apple/Work/Aspose/GitHub/aspose-app-health-and-recovery-redirect`, `index.html` = `404.html`, JS keeps path, query and #anchor; old root and `/archive/` go to `/aspose.app/`; Pages: Deploy from a branch, main).
- All reports move to a private domain soon (SK, 2026-10-20); until then they are public (noindex).

**What changed on 2026-10-27 (report redesign, SK: "numbers speak more than text"; pilot on aspose.cloud):**
- **Overview layout** (tenant YAML `report: manager_view: true`, aspose.cloud only): one page, two parts without audience labels (SK): **Overview** (age line "audit data from <date> · N days old", amber after 14; 5 number tiles: Health with trend, Search clicks and impressions with % vs previous 28 days and six months ago, Open issues by severity, Since last run; Health by area; **Top actions required** as a table: score, issue, severity, pages, clicks, effort) then **Details** (findings, changes, coverage numbers, reference). A single-host page hides the Host health table (it repeats the Health tile).
- Area tiles: issue counts with broken in red, then the biggest loss. **SK chose the badge over a cap** (a broken issue does not cap its area at 59: a 0-click problem would sink the score like a sitewide one).
- **Health history** now records host health and area scores per set of runs (`record_health`; older entries have families only); `host_trend` feeds the Health tile (trend from the second run; aspose.cloud's first point 2026-10-27, dated at recording, not at the audit date).
- **Method page redesigned:** pipeline diagram (7 steps with key numbers), one audits table, health and priority-score formulas with weight tables, grade bar, worked example, limits as bullets, glossary table (`scripts/templates/method.html`, own scoped CSS `.mth`).
- **Decided for aspose.app (not built):** property number = host health weighted by Search Console clicks (SK agreed); discuss before building, because products.aspose.app has ~1.5M of ~1.5M clicks, so the number is effectively products'. Property page = one card per host (health, clicks, impressions, issues, area scores), host page = Overview + Details; Top actions required (top 5 across hosts) on the property page. **Search Console for www, forum, dashboard, purchase, metrics, status:** SK will try to get access (ideal: `sc-domain:aspose.app` Restricted for the service account); until then those hosts show GA4 sessions. SK prefers GSC (it measures Google search clicks, the same source as findings' clicks at stake).
- Live/archive: aspose.cloud snapshot 2026-10-27 ("Overview and details…"); the live version before it was 2026-10-26-3.
- Property page with host cards replaces the brief single-host redirect (snapshot 2026-10-27-2).
- **Wording (SK, 2026-10-27): property = domain, host = subdomain** on everything people read (dropdowns, headings, table columns, method page, fix guide, landing page); URLs and code names unchanged. **No A–F letters on the new layout** (numbers only, colours keep the 90/75/60/40 cut-offs; the method page shows ranges and explains the letters older reports still show). aspose.app's family cards and summary keep letters until aspose.app moves to the new layout (open question to SK: drop them then, recommended). **Breadcrumb** `All domains › <domain> › <subdomain>` on published report pages (replaces the "one host of" line and "All reports"), also on the method and fix guide pages.
- **Domain page: full-width subdomain rows** (replace the host cards): score with ⓘ, clicks and impressions with % vs previous and six months ago, open issues, since last run, the five area scores with broken badges, link to the subdomain page; may take two lines (SK: keep all this information). Sort A to Z by default; a sort menu (A to Z, lowest score, most clicks) when there is more than one subdomain. Hover (title) explains a score's calculation with exact points (one decimal, so items add up); ⓘ also opens it on tap (no hover on phones). SK: hover only for calculation info, never for the numbers themselves. Phones: rows stack into blocks, every cell carries its own label.
- **Phone overflow fixed on every page** (header switches wrap; open Reference panels and the method diagram scroll inside their boxes); all report pages and the method page fit 390px. Host pages open a finding from `#f-<id>` (also behind "Show more"). `host_trends` gives every host its trend.
- GSC access checked 2026-10-27: aspose.app still products, about, blog, releases, websites only; www, forum, dashboard, purchase, metrics, status have none (they stay on GA4 sessions). Newly readable: blog.aspose.com, blog.groupdocs.com, blog.conholdate.com (for the .com tenants later).

**What changed on 2026-10-26:**
- Architecture diagram version 10 (blog source repos, link check as step 6); link check on conholdate.cloud (run 5).
- "How this audit works" moved to its own page `/method/` (see Site layout). All four tenants archived before (live pages downloaded where not yet archived) and snapshotted after ("How this audit works on its own page").
- **Health by area (SK, 2026-10-26; trial on aspose.cloud only, tenant YAML `report: area_scores: true`):** a row at the top of the Summary: Overall plus one score per area = finding `dimension` (`core/scorecard.AREAS`: crawl "Crawl & indexing", onpage "On-page content", intl "Languages", ai "AI readiness", perf "Speed"; other dimensions follow when present). Each area is the scorecard formula on its own findings only, so the overall is never above an area (note under the row). Tiles name their two biggest losses by fix-guide plain name and open that dimension's findings. Speed with no real-user data and no findings shows "–" ("no real-user data · N pages, lab median M"), not 100 (aspose.cloud: 0 of 12 pages have field data, lab median 74). An area whose audit did not run shows "not checked". Shown only when the page covers one host (overall = its Host health row). SK chose numbers over status pills after hearing the caveats (weights are unvalidated; points ignore traffic; target gaming). **Family cards unchanged (SK: may decide later).** aspose.cloud today: Overall 66 C, Crawl 88, On-page 90, Languages 83, AI 95, Speed –.
- **Submitted sitemaps table** was empty on the three .cloud reports (no `gsc_sitemaps_snapshot`). Snapshots added from the GSC API (gsc MCP `list_sitemaps`, 2026-10-26: one root index each, Success, 13,525 / 11,070 / 172 discovered). `build_report.gsc_comparison` builds the table from the run's sitemap list when the discovery run predates the snapshot (no rerun needed). prioritize.py also reads the snapshot (discovered counts size sitemap findings) at its next run.
- ~~Phone overflow~~ fixed 2026-10-27.
- **Short technical check names (SK: "we are techs and all managers are techs too"):** all 82 fix-guide names rewritten (`core/fix_guide.py`), e.g. "Internal link to 404 page", "Empty page without JavaScript", "Missing supported languages", "LCP poor", "No x-default hreflang". **Every term is explained in place (SK):** `core/fix_guide.TERMS` (18 terms: LCP, INP, CLS, TTFB with our exact thresholds from `core/audit/perf.THRESHOLDS`, Core Web Vitals, hreflang, x-default, canonical, noindex, H1, JSON-LD, lastmod, Soft 404, llms.txt, Lighthouse, Meta refresh, viewport, 4xx/5xx); reports mark them (dotted underline + small "?", definition on hover, focus or tap; a term inside a link explains itself instead of following it); the method glossary is generated from TERMS (`build_report.method_html`, `__TERMS__`); the fix guide page marks them with title tooltips (`mark_terms`).
- **Score explanation panel** (one page-wide popover for score calculations `data-x` and terms `data-t`): list of points lost with numbers aligned, total, arithmetic, rule; replaces the unreadable one-line tooltip (SK).
- **Scores round halves up (SK: 65.5 → 66, 65.4 → 65)**: `core/scorecard.half_up` in the scorecard and the family rollup (Python `round()` rounded halves to even). Changed live scores by +1: blog.aspose.cloud 66 → 67, its Crawl & indexing 88 → 89, about.aspose.app 90 → 91, forum.aspose.app 92 → 93, /page/ 72 → 73. Recorded health history keeps the old values for the current runs (one-time +1 in the next trend).
- Archive: aspose.app 2026-10-27 (downloaded, before) and -2 (after); aspose.cloud 2026-10-27-4.
- **Score bars (SK, 2026-10-27; Overview layout only):** `sbar()` in the template: always 0 to 100, filled in the band colour, 4px rounded ends, 2px surface gaps at 40/60/75/90, hatched empty bar for "no data"; aria-hidden (the number stays primary). Subdomain page: Health by area is a list (score, name, bar, issues and biggest loss) with a 0-40-60-75-90-100 scale under it; rows open the area's findings, the number opens its calculation panel. Bars also under the Health score tile and on the domain page rows (score and each area). Rejected on purpose: a stacked bar of area losses (area losses do not add up to the overall: one root cause counts once, minor issues capped) and bars for clicks or counts (no fixed scale; a trend line fits once there are runs). Snapshot aspose.cloud 2026-10-27-5.
- **groupdocs.cloud and conholdate.cloud on the Overview layout** (SK, 2026-10-27; tenant YAML `report: area_scores, manager_view`): archived before (2026-10-27, downloaded) and snapshotted after (2026-10-27-2). Today: blog.groupdocs.cloud 73 (Crawl 89, On-page 92, Languages 88, AI 95), blog.conholdate.cloud 81 (100, 96, 93, 93). All three .cloud domains now share the layout; only aspose.app keeps the old one (decisions pending: overall number, family letters).
- **Changes on tiny numbers:** below 20 the tiles and rows show the previous value ("previous: 2") instead of a percentage (1 click vs 2 was "−50%").
- **Fix tracking for blogs (SK, 2026-10-27): "fixed / new / still open" per blog subdomain.** Unit = one item of an exact check (link check: each link, each missing language of a post, each unsupported language); sampled checks (crawl, text, speed) stay at finding level. Fixed % = fixed ÷ (fixed + still open) (SK's example: 200 of 1,000 = 20%; 1,000 new → 200 of 2,000 = 10%), always shown with fixed, new and still open next to it. A gone item is "fixed" when its post file still exists in the clone, "removed" when the post was deleted; a returning item reopens. Ledger `reports/<tenant>/items.json` (`core/items.py`, `scripts/track_items.py`), incremental per link-check run. Baseline = each blog's first link check (SK agreed: earliest complete data): blog.aspose.cloud 1,556 items (22 Oct), blog.groupdocs.cloud 779 (22 Oct), blog.conholdate.cloud 4 (26 Oct). **First quick run 27 Oct: item sets identical** (0 fixed, 0 new; 88 new aspose.cloud posts added no issues). **Display simplified (SK, 2026-10-27): "Link-check issues · scanned <date>" with issues (= fixed + open), fixed, open and a small fixed %; no "new", no baseline on the pages** (new issues show as a growing issue count; the first-scan date appears only in the Details table caption, so "fixed" has a period). Tile on subdomain pages, per-check table in Details, column on domain and Blogs rows. aspose.cloud's first health-history entry was rescored with half-up rounding (66 → 67, crawl 88 → 89, noted in the entry) because the old value showed a false "+1" trend. Discovery keeps only 10 example URLs per finding, so sitemap issues cannot count fixes yet (follow-up: record full lists). blog.aspose.app has no blog repo configured, so no link check and no fix counts.
- **`scripts/run_cycle.py <tenant> [--quick] [--from STEP]`** runs the audit steps in order (loads .env itself, logs to `data/<tenant>/cycle-<date>.log`, stops at the first failure). `--quick` = discover, audit_links, track_items, prioritize (exact checks only, no LLM, ~25 min for the three .cloud blogs): weekly and after a translation batch. Before the link check it fast-forwards each blog clone (`git pull --ff-only`, SK agreed) and stops untouched if the clone has local changes or diverged. Schedule (planned, on the Mac; GitHub Actions later if needed): quick weekly, full monthly; push always asks SK.
- **Blogs page `/blogs/` (SK, 2026-10-27):** one page across domains with a row per blog subdomain (blog.aspose.app, blog.aspose.cloud, blog.conholdate.cloud, blog.groupdocs.cloud), Top actions required across all blogs, **no overall score** (SK agreed: an average hides the weak blog), no archive of its own (built from the archived domain reports). Membership: tenant YAML `collections: {blogs: [<host>]}`; `build_site.COLLECTIONS` names the pages (`/blogs/` reserved). Each member is prepared exactly as its own subdomain page (`build_report.prepare`, `--areas` forces area scores, so blog.aspose.app gets areas although aspose.app is still on the old layout); finding ids are prefixed `<host>/<id>` there (`_orig_id` for links to `/<host>/#f-<id>`). The Domain dropdown lists it under "Across domains"; the landing page lists it. Area names for manual-only dimensions: `core/scorecard.OTHER_AREAS` (ux → User experience). The page's data age shows the oldest member data (aspose.app's discovery from 9 Oct today, so amber).

**What changed on 2026-10-22 (details under Open discussions, "Tenants 3 and 4"):**
- Tenants 3 and 4: `aspose.cloud` (blog.aspose.cloud, GA4 252280807) and `groupdocs.cloud` (blog.groupdocs.cloud, GA4 252358764); GSC blog properties readable; sample option A (20 pages per template); `tag` URL template in all three .cloud tenants; `translation_languages` (SK's supported list) in each .cloud tenant.
- **Link check** (`core/audit/links.py`, `scripts/audit_links.py`): every internal link of every post read from the blog's local repo, checked on the live site. Found SK's known bug (English link although the translation exists: 64 / 72 links) and a bigger one: the translation agent prefixes every internal link with the language, also when the target was never translated (old posts deliberately stay English), so 1,389 links on aspose.cloud return 404 (798 written by the current agent in 2026, still ongoing). Root cause: link localization is an LLM prompt rule in `conholdate/blog-translation-agent` (`translator.py` rule 5) with no existence check. Fix lists for SK's agent: `reports/<tenant>/link-audit-<date>-run<id>-issues.csv`.
- **SK is the translation team** (owns the translation agent for blog.aspose.cloud, blog.groupdocs.cloud, blog.conholdate.cloud, blog.aspose.com, blog.conholdate.com; no longer blog.groupdocs.com, whose issues still go in reports). Phase 1 only identifies; his agent fixes.
- First full cycle for both new tenants; reports and "First run" snapshots live.
- Text check found `seoTitle` copied from other posts (632 of 1,240 aspose.cloud English posts share their search title; one title 81 times).
- Bug fixed (SK spotted): the Sections table showed the homepages row as `//`; now `/ (homepages)`.
- No person names in anything committed or published (the link check records commit id, date and message, never the author).
- Commit email history rewrite (see Commit identity).

**What changed on 2026-10-20 (details in the bullets below and in Status):**
- Text check built and run (first LLM use); typo severity agreed; a soft-404 gap fixed in code.
- Tenant 2 `conholdate.cloud`; per-tenant folders `data/<tenant>/`, `reports/<tenant>/` (`core/paths.py`); every script takes `--tenant` / `TENANT`.
- New service account `sk-serv-acc@health-and-recovery.iam.gserviceaccount.com` (project `health-and-recovery`) for every tenant; tenant YAML `google_credentials_env` picks the `.env` key variable, no fallback between keys. The old account (`sk-service-acc@aspose-app-health-and-recovery`) can be deleted once Claude Code was restarted (the running `gsc` MCP server held the old key).
- Repo renamed to `health-and-recovery` by SK; `github` remote and links updated; redirect repo for old links.
- Host health table (one row per host; products.aspose.app rolled up from its families), host pages, property/host switches, shared fix guide page.
- api.products.aspose.app dropped from the aspose.app tenant (API/backend host, not a website).
- Bug fixed: the Host health section reused `id="hosts"` and emptied three Reference tables; a test now rejects duplicate ids.

**Scores today (half-up rounding from 2026-10-27):** aspose.app hosts: about A 91, forum A 93, blog B 86, metrics B 85, www B 75, status C 67, dashboard C 62, releases C 60, products D 56 (families 72 by clicks − 16 host-wide; lowest /drawing/ F 19), websites D 48, purchase D 46. blog.conholdate.cloud B 81 (B 86 before the link check). blog.aspose.cloud 67 (no letters on the new layout), blog.groupdocs.cloud C 73.

**Next session, start with:**
1. ~~Architecture diagram~~ Done 2026-10-26 (version 10: blog source repos, step 6 audit_links.py, prioritize is step 7).
2. ~~Link check on conholdate.cloud~~ Done 2026-10-26 (run 5: 141 links in 93 posts, 4 wrong-language links in 3 Arabic posts, all from one 2025-08-12 commit "configured and published translations", not the agent's; no 404s; health B 86 → B 81).
3. **Priority 4** (`findings`, then `crawl` MCP servers). The functional auditor is **postponed** (SK, 2026-10-20).
4. **Soft 404 fix (code only, 2026-10-20):** takes effect at the next aspose.app crawl run; then count how many psd (and other) sitemap URLs end at `page404` (see Status, "Text check").
5. **Remind SK** to get a dedicated LLM key (the text check still borrows the translation agent's), to delete the old service account after a restart, and to turn GitLab's "Allowed to force push" on `master` off again if not done.
6. Watch: **ocr is intermittently failing** (crawl audit run 15: 1 of 18 sampled pages HTTP 502). Re-check in the next aspose.app run.
7. Later (SK): the .com blogs (blog.aspose.com, blog.groupdocs.com, blog.conholdate.com; language lists and GA4 ids noted under Open discussions); per-product or per-platform grouping of blog posts (decide after looking at the first run).
8. Offered, not decided: read submitted sitemaps live from the GSC API instead of the pasted `gsc_sitemaps_snapshot`; a per-host share fix in the scorecard; per-family pages `/products.aspose.app/<family>/` (SK: later); Total's format pages share one generic description. Open questions for SK are under "Open discussions" (shared problems severity, Aspose.ai comparison, sample transparency, a "Speed" pill on family cards), plus whether short status incident pages should count in "almost no text without JavaScript".

**Live:**
- Landing page https://shoaibkhan-aspose.github.io/health-and-recovery/; aspose.app https://shoaibkhan-aspose.github.io/health-and-recovery/aspose.app/ (archive https://shoaibkhan-aspose.github.io/health-and-recovery/aspose.app/archive/); conholdate.cloud https://shoaibkhan-aspose.github.io/health-and-recovery/conholdate.cloud/ (archive https://shoaibkhan-aspose.github.io/health-and-recovery/conholdate.cloud/archive/); aspose.cloud https://shoaibkhan-aspose.github.io/health-and-recovery/aspose.cloud/ (archive https://shoaibkhan-aspose.github.io/health-and-recovery/aspose.cloud/archive/); groupdocs.cloud https://shoaibkhan-aspose.github.io/health-and-recovery/groupdocs.cloud/ (archive https://shoaibkhan-aspose.github.io/health-and-recovery/groupdocs.cloud/archive/); fix guide https://shoaibkhan-aspose.github.io/health-and-recovery/fix-guide/; host pages https://shoaibkhan-aspose.github.io/health-and-recovery/<host>/. Rebuilt by GitHub Actions (`scripts/build_site.py`) on every push to `master`.
- Architecture page (private, version 10 = blog source repos and the link check as step 6, four tenants, 2026-10-26; PNG 1280x1200, headless Chrome `--window-size=1280,1200`): https://claude.ai/artifact/3zrEcbrV1WxN9nfjvS7Kxm, source `docs/architecture/site-health-architecture.html`.
- Archive aspose.app (`reports/aspose.app/archive/`): 2026-10-12 (before the restructure), 2026-10-15 (before the speed audit), 2026-10-15-2 (after the speed audit), 2026-10-16 (before the AI audit), 2026-10-16-2 (after the AI audit and crawl audit run 15), 2026-10-20 (after the text check), -2 (text check run 23, before the per-tenant layout), -3 (host cards and shared fix guide), -4 (host table), -5 (products row), -6 (without api.products, before fixing the empty Reference tables).
- Archive conholdate.cloud (`reports/conholdate.cloud/archive/`): 2026-10-20 (first run), -2 (after the text check, host health), -3 (host table; rebuilt from commit c63dbbf), -4 (before fixing the empty Reference tables); 2026-10-26 (with the logo, before the link check; downloaded), -2 (after the link check).
- Archive aspose.cloud and groupdocs.cloud: 2026-10-22 (first run). aspose.cloud also: 2026-10-26 (with the logo, before health by area; downloaded), -2 (health by area, submitted sitemaps).
- Older shared discovery report (private, not updated since run 7): https://claude.ai/artifact/MUUTzbXEymKq4tw5mmmPA5

**Latest data:**
- aspose.app: full cycle 2026-10-27 (`scripts/run_cycle.py`): discovery run 9, full crawl audit run 24 + status.aspose.app re-crawl run 28 (run 24 caught a transient HTTP 500 on /dashboard → /auth/login that would have dropped status 67 → 30), AI audit run 25, speed audit run 26, text check run 27 (no new LLM findings); superseded run JSONs (crawl 15, AI 16, speed 12, text 23) deleted. 400 findings in the store. Snapshot "Full run 27 Oct" (archive 2026-10-27-4; live version before it downloaded as 2026-10-27-3). Scoring flaw found, fix agreed as the next separate step: a template's share is counted within the template only, so a one-page template can cost −40 for a whole subdomain; planned fix weights by the template's estimated share of the subdomain's pages, rolled out to all tenants at once with history rescored, before/after shown to SK first.
- conholdate.cloud: discovery run 1, crawl audit run 1 (15 pages), AI audit run 2, speed audit run 3 (8 pages), text check run 4 (no findings), all 2026-10-20; link check run 5 (2026-10-26); traffic window 2026-09-26..10-23; GSC `https://blog.conholdate.cloud/` and GA4 253119926 (one property for all conholdate.cloud hosts). 7 open findings. Local repo `/Users/Apple/Work/Aspose/GitHub/blog.conholdate.cloud-PROD/blog.conholdate.cloud`.
- aspose.cloud: discovery run 1, crawl audit run 3 (40 pages), AI audit run 4, speed audit run 6 (12 pages), text check run 7, link check run 8, all 2026-10-22; traffic window 2026-09-22..10-19 (710 clicks; 961 six months ago; 89% on translated pages). Local repo `/Users/Apple/Work/Aspose/GitHub/blog.aspose.cloud-PROD/aspose-cloud-blog`.
- groupdocs.cloud: discovery run 1, crawl audit run 2 (32 pages), AI audit run 3, speed audit run 5 (8 pages), text check run 6, link check run 7, all 2026-10-22; traffic window 2026-09-22..10-19 (577 clicks; 1,483 six months ago; 85% on translated pages). Local repo `/Users/Apple/Work/Aspose/GitHub/blog.groupdocs.cloud-PROD/groupdocs-cloud-blog`.

**Full cycle** (on the Mac, from the repo, `.venv` active; per tenant: `export TENANT=aspose.app`, `conholdate.cloud`, `aspose.cloud` or `groupdocs.cloud`, files go to `data/$TENANT/` and `reports/$TENANT/`):
```bash
set -a; source .env; set +a
export TENANT=aspose.app
python scripts/discover.py --quiet           # 15 min; inventory + sitemap findings
python scripts/audit_crawl.py --quiet        # 25 min; all hosts + families (or --sections a,b); incl. AI page checks
python scripts/audit_ai.py --quiet           # 5 min; AI crawler access (robots.txt, firewall), llms.txt per host + family
python scripts/audit_perf.py --quiet         # new tenant: run prioritize.py once first (picks top-traffic pages); ~40 min; speed (PageSpeed Insights), 2 top-traffic pages per template
python scripts/audit_text.py --quiet         # ~5 min (seconds when cached); LLM text check of the crawl audit's pages
python scripts/audit_links.py --quiet        # blogs with a local_path repo only; ~20 min for blog.aspose.cloud; pull the clone first
python scripts/prioritize.py                 # traffic, scores, reports/$TENANT/findings.json, traffic-summary.json
python scripts/build_report.py --out reports/$TENANT/discovery-latest.html --snapshot "After <what changed>"
#   --snapshot freezes this report into reports/$TENANT/archive/ (served at /$TENANT/archive/<date>/) and records
#   family health in reports/$TENANT/health-history.json (trend in "Changes since the last run"); after every full run
python scripts/build_site.py --out /tmp/site   # optional local preview of the whole Pages site
# delete superseded run JSONs; then
git add -A && git commit -m "..." && git push github master   # Actions rebuilds the Pages report + archive
```

**Working rules from SK (keep):**
- **Commit email: always `shoaib.khan@aspose.com`** (SK, 2026-10-22). Set in this repo's `.git/config`, because something on the Mac switches the global `~/.gitconfig` to SK's personal address; check `git log -1 --format=%ae` after every commit. History rewritten 2026-10-22 (`git filter-repo --mailmap`, 80 of 96 commits moved from the personal address; dates, messages and files unchanged; all commit ids changed; backup bundle kept outside the repo; old → new id map: Claude doc https://claude.ai/artifact/LyhQxpxJhcb3L9twbCJ41k).
- Commits: SK is the only author and committer. Credit Claude with a plain last line `Assisted by Claude Code` (SK, 2026-10-12; exactly this wording, no model name); **never a `Co-Authored-By: Claude` trailer** (GitHub would show Claude as co-author). Leave old commits as they are.
- Commit at each logical step; push to `github` (GitLab `origin` mirrors GitHub).
- Report changes apply to the **latest report only**; never regenerate older report pages or run JSONs.
- **Archive before anything replaces the live report (SK, 2026-10-15: "store in archive whatever is necessary and don't forget it"):** before pushing a report whose structure or data changed, check `reports/<tenant>/archive/index.json`. If the version live on Pages is not archived yet, download it (`curl` the tenant's Pages URL `/<tenant>/` into `reports/<tenant>/archive/<date>.html`, add an index entry "…, before <change>"; it equals a build of the last commit), then build the new report with `--snapshot "After <change>"`. Every version that was ever live must end up in the archive.
- **No person names in anything committed or published** (follows from the rule below, 2026-10-22): the link audit records the commit id, date and message of each issue, never the git author.
- **Report wording names issues, never blames teams** (SK, 2026-10-13): no "worst", "failing", "weak"; the verdict names no family and shows totals ("2 families graded F and 6 graded D. Biggest risk: <issue> in 3 families and 1 host (13k clicks at stake)"); top risks list affected places alphabetically (or count them when more than 4). Priorities and findings stay per family (working lists for teams).
- Discuss before building when SK asks a question ("discuss first", "do not implement").
- **Honest verdicts (SK, 2026-10-20):** comment honestly on every suggestion SK makes, up front: is it a good idea, what it costs, where he is wrong (e.g. a wrong domain name). No yes-man answers.
- **Archive every tenant** before a push that changes its live report (not only aspose.app). Small layout changes (a dropdown, a link) need no snapshot.
- **LLM use (SK, 2026-10-20):** the internal endpoint is shared by the team. Run at normal speed (4 parallel calls) and back off only on trouble (all calls pause 30 s after a failure); not one-at-a-time. Sending public aspose.app page text is fine. LLM findings are reviewed by hand after each run that sends new text; false positives go to `audit.text.ignore` in the tenant YAML with a reason, and a false positive that was already published is deleted from the findings store (not "resolved"), so the report never claims a fix that did not happen.
- **Domain facts:** Aspose.Total (`/total/`) is the bundle of all Aspose products (Words, PDF, Cells, ...): broad format lists on its pages are correct.
- Keep the architecture diagram in its current shape; update it when the architecture changes (see "Architecture diagram" below).
- The Pages report stays `noindex, nofollow`; traffic numbers are published as is for now (moves to a private domain later).

**Report restructure (built 2026-10-12, SK said go for A+B+C):**
- Order: header verdict -> sticky contents bar -> Summary ((c) grade distribution + (b) click share per grade and D/F families with >= 5% of clicks; key numbers; 5 top risks, one per kind of problem) -> Product families -> Priorities (top 10, plain names, how-to-fix links) -> Shared problems (same check in 3+ families) -> All findings -> Changes since the last run (new / resolved / family health trend) -> Fix guide (one row per check, area filter) -> Reference (collapsed: crawl audit per host, hosts, sections, submitted sitemaps) -> How this audit works (method, health, score, samples, glossary).
- Data: `core/fix_guide.py` (55 checks: plain name, means, impact, fix, verify; test keeps it in step with the auditors), `core/report_view.py` (confidence: complete / strong / partial / to confirm; merge of findings with one sitemap root cause into the worst; shared problems; top risks; grade summary; run changes; health trend), wired in `build_report.add_views`.
- Traffic lost (built): prioritizer measures each finding's share six months earlier; score = traffic factor of max(at stake, 0.5 x lost). drawing blockers 29 -> 56. Impact table shows "Six months ago" with the loss.
- Archive (built): `reports/archive/` + `index.json`, `scripts/build_archive.py` (Pages /archive/), `build_report.py --snapshot LABEL`; first snapshot 2026-10-12 = the report before the restructure (byte-identical to what was live). SK: snapshot before structure changes AND after every full run.
- Fix guide shows area headings and a severity column (severity per check comes from the auditors via `core/fix_guide._severities`). Report links (how this audit works, previous versions) live in the footer, not the header. Family sort storage key is `fam-sort-v2` (reset everyone to A-Z once).
- Reference tables are semi-collapsed (SK, N=5): open by default, each row marked ✗ broken / ⚠ warning / ✓ fine, sorted by status then size; the top 5 show (all broken rows if more), the rest behind "Show all"; a table with nothing to fix stays closed and says "all N fine".
- Hand-written takeaways (`reports/*-notes.txt`) are no longer shown (SK: too much text); the files remain but are unused.
- Later polish (2026-10-13): dates read "6 Oct 2026" everywhere except inside URLs (`day()`, `readable()` in the template; archive list too); Search Console windows show their length ("9 Sep 2026 to 6 Oct 2026 (28 days)", `span()`); fix guide area headings are distinct bands (accent rule, tint, check counts); the grade summary is spaced plain text "9 B   12 C   6 D   2 F" (SK tried coloured grade chips and rejected them: keep it plain). Family cards default A to Z, extremes strip removed, health sorts named lowest/highest. Card status (Sitemap, Pages, Canonical, hreflang) is a row of pills (SK, 2026-10-15): green ✓ / amber ⚠ / red ✗ with soft tints, fine ones green too (SK: green motivates teams, red catches management); symbols stay for colour-blind readers; small layout changes like this are not archived.

**Small facts worth knowing:**
- Logo (2026-10-22): source files in `docs/brand/` (mark, horizontal lockup, favicon, 512px PNG); `core/brand.py` inlines the favicon (data URI) and the mark (inline SVG) into every built page: report header, landing page, fix guide, archive list. Frozen snapshots keep what they had. A small layout change, no snapshot.
- Google data caches (gitignored, in `data/`): `traffic-<tenant>-<start>_<end>.json` (current window: GSC pages + GA4) and `history-<tenant>-<start>_<end>.json` (previous 28 days, six months ago). `prioritize.py` reuses a cache when the window matches and fetches when the window moves (a new day); `--offline` uses the newest cache without Google calls. The committed result is `reports/traffic-summary.json`.
- Known gap: the fix guide and scorecard know `canonical_broken` (canonical pointing at a 4xx/5xx page), but the crawl auditor does not emit it as its own check yet; it still reports `canonical_elsewhere`, and the scorecard and confidence treat it as broken from the canonical-target status in the evidence. Emitting it is a small auditor change for the next audit work.
- Report browser storage (per viewer): `fam-sort-v2` (family sort, default A to Z), `fam-view` (rows/grid), `disc-filters` (findings filters). Renaming a key resets everyone once.
- GitHub Pages: Settings → Pages → Source is "GitHub Actions"; the workflow builds the report from committed files only (no Google calls, no `data/`).

**Open discussions (not decided or not built):**
- Shared problems severity (SK asked 2026-10-13 which row is most severe): each row's label is the worst case in the group (canonical: really broken only on /cells/, incorrect in 8; sitemaps: broken on omr and drawing, gis is a leftover; page errors: broken in all 3). Offered: show the mix ("Broken in 1 · Incorrect in 8") and sort by families really broken, then clicks. Not answered.
- Compare this report with the Aspose.ai Website Health page (https://aspose.github.io/aspose-ai-website-health/): SK asked 2026-10-13, then interrupted before an answer. Earlier notes on that page are under "Ideas from the Aspose.ai Website Health monitor".
- Sample transparency (cells question, 2026-10-12): still open: (1) "Sample: N pages · L languages" on each card, clickable like Sitemap; (3) sample per tool, not only per template, for big families; (4) bigger samples for high-traffic families. (Confidence labels, idea 2, are built.)
- Tenant 2 **`conholdate.cloud`** (config added 2026-10-20, SK: tenant `conholdate.cloud` with only `blog.conholdate.cloud` for now, other hosts later): `tenants/conholdate.cloud.yaml` (Hugo/PaperMod, repo `conholdate-cloud/blog.conholdate.cloud`, 23 languages incl. zh-hant, templates home/listing/post/category; all live sitemap URLs classify). **New service account (SK, 2026-10-20): `sk-serv-acc@health-and-recovery.iam.gserviceaccount.com`** (project `health-and-recovery`, key in `/Users/Apple/Work/Aspose/keys/service accounts/`), **now used for every tenant** (replaces `sk-service-acc@aspose-app-health-and-recovery`, which SK may delete): `.env` `GOOGLE_APPLICATION_CREDENTIALS` (default: aspose.app, `gsc` MCP server, PageSpeed) and `GOOGLE_CREDENTIALS_HEALTH_AND_RECOVERY` (named by conholdate.cloud's `google_credentials_env`) both point at its key. Tenant YAML `google_credentials_env` picks a tenant's key variable, no fallback between keys; `check_access.py` and `prioritize.py` use it. Access check 2026-10-20 with the new account, all pass: aspose.app 5 GSC properties + GA4 253117495; conholdate.cloud GSC `https://blog.conholdate.cloud/` (Restricted; 28 days: 1 click, 80 impressions, 1 sitemap, no errors) + GA4 **253119926** (one property for all conholdate.cloud hosts: aspose, www, websites, blog, reference, forum, metrics, products, about, releases; blog 52 sessions / 1 organic); PageSpeed works (one test call). The GA4 Admin API is off in the new project (not needed). **First run 2026-10-20** after the per-tenant layout was built: discovery run 1 (24 sitemaps, 163 URLs, 23 languages, no findings), crawl audit run 1 (15 pages), AI audit run 2 (no llms.txt), speed audit run 3 (8 pages, median lab score 96, no real-user data), prioritized; 6 open findings; text check not run. Earlier notes (2026-10-14): core is ready; gaps are no GSC/GA4 access for the service account, report outputs are single-tenant (`reports/findings.json`, `traffic-summary.json`, aspose.app wording), blog needs `url_templates`/sample config, and the "standalone, not blog-team-tools" scope note. Plan offered: per-tenant subfolders on the same Pages site (one deploy builds all tenants). Open: separate vs combined report, other Conholdate blogs, Conholdate data public.
- "Speed" pill on family cards (offered 2026-10-15; SK: keep undecided, revisit later): a fifth status from the `speed` scorecard group. Speed findings are only not_optimized/improvable, so it would be amber (10 families today) or green, never red. Needs a 4th, grey "no data" state: only 78 of 310 measured products pages have real-user data, so green without data would claim "fast" without evidence. Recommended: add it with the grey state.
- ~~Pages URL rename~~ Done 2026-10-20: repo renamed to `health-and-recovery` by SK (see Start here). Redirect repo with the old name built and live (2026-10-20).
- **Tenants 3 and 4, `aspose.cloud` and `groupdocs.cloud` (SK, 2026-10-22; only their blogs, config added, not run yet):** same stack as blog.conholdate.cloud (Hugo/PaperMod, S3 + CloudFront; repos also have Ceph deploy workflows). GA4 252280807 / 252358764; GSC blog properties readable; access check passes. Sample option A (`per_template_by_host` 20; 13.5k / 11k sitemap URLs). `tag` URL template (`/tag/<name>/`) added to all three .cloud tenants. Old posts are **deliberately not translated** (SK): English-only posts are not a finding. `translation_languages` in each tenant YAML = SK's supported list (matches the repos; aspose.cloud's config/sitemap also advertise `cs`, `id`, which are not supported). Per-product vs per-platform grouping: decide after the first run.
  - **SK is the translation team** (owns `conholdate/blog-translation-agent`); findings on translated content go to his agent for fixing (Phase 2).
  - **Internal link bug (repo scan 2026-10-22, read-only):** translated posts link to `/<lang>/<post>/` although that post has no translation → 404. aspose.cloud 1,200 links (798 written by the current agent in 2026, still ongoing; 402 by older commits incl. "localized internal link FIX", 2025-06), groupdocs.cloud 1 (plus 129 damaged/copied-broken links from 2023 translations), conholdate.cloud none. SK's known bug (English link although the translation exists): aspose.cloud 2 posts, groupdocs.cloud 1, conholdate.cloud 4 links in 3 files. Damaged URLs (`/pt//total/...`, cut slugs): 45 / 56. ~490 groupdocs links to old WordPress `/category/<x>/` (404; `/categories/<x>/` also 404). Cause: link localization is an LLM prompt rule (`translator.py` rule 5) with no existence check. 2 aspose.cloud posts (2016) miss th and vi.
  - **Link auditor built (SK chose option 2, 2026-10-22):** `core/audit/links.py`, `scripts/audit_links.py`, source `link-audit`, 6 checks (`link_missing_translation`, `link_damaged`, `link_wrong_language`, `link_broken`, `translation_partial`, `language_unsupported`; fix guide area "Links and translations"; scorecard groups "internal links" and "translations"). Links come from every post in the host's `local_path` repo (inline, reference and HTML links, outside code; CR-only line endings normalized; downloadable files skipped); a target exists if the latest discovery inventory lists it, else it is fetched once (200 = exists, 404/410 = missing, anything else unchecked and never reported). Translation existence (for wrong-language links) comes from the sitemaps only. `git blame` names the commit per issue; tenant `audit.links.translation_commits` marks SK's agent. Findings: one per check and host, exact affected pages (Prioritizer `EXACT_PAGE_SOURCES`); full fix list in `reports/<tenant>/link-audit-<date>-run<id>-issues.csv`. The clone is never pulled by the script (SK's working copy); a last commit older than 7 days is warned about. Run 1 aspose.cloud found a false positive (`.csv`/`.tsv` downloads fetched with a trailing slash); fixed and rerun as run 2. Live spot check of run 1: 22 of 24 as expected (the 2 were that bug).
  - **First full cycle 2026-10-22** (both tenants): discovery run 1 (13.5k / 11k URLs; findings: duplicate sitemap URLs, cs/id sitemaps without lastmod), crawl audit (40 / 32 pages), AI audit (no llms.txt), speed audit rerun after prioritize (a new tenant has no traffic cache, so the first speed run picks pages blind: run prioritize.py once before audit_perf.py; lab median 74 / 93, no findings), text check (11 / 3 pages "about a different product": all real, `seoTitle` front matter copied from another post; repo count: 632 of 1,240 aspose.cloud English posts share their seoTitle with another post, one title 81 times; groupdocs.cloud 76), link audit. Traffic (GSC 2026-09-22..10-19): aspose.cloud 710 clicks (six months ago 961), groupdocs.cloud 577 (six months ago 1,483); 89% / 85% of clicks land on translated pages. Health: aspose.cloud C 66, groupdocs.cloud C 73. Top scores: link findings on both. The first link-audit runs and first-run snapshots carried git author names; deleted unpublished and rerun (link check aspose.cloud run 8, groupdocs.cloud run 7: link_missing_translation 1,389 / 187, link_broken 71 / 511, link_wrong_language 64 / 72, link_damaged 26 / 9). Snapshots "First run" taken from these. Committed and pushed 2026-10-22 (100804d..722b326); live at /aspose.cloud/, /groupdocs.cloud/, /blog.aspose.cloud/, /blog.groupdocs.cloud/. Next: architecture diagram (new input: blog source repos, link audit).
  - **Supported translations of the .com blogs (SK, 2026-10-22; noted only, no .com work until the .cloud tenants are done):** blog.aspose.com: ar, cs, de, es, fa, fr, he, id, it, ja, ko, pl, pt, ru, sv, th, tr, uk, vi, zh, zh-hant. blog.groupdocs.com: ar, cs, de, es, fa, fr, he, id, it, ja, ko, nl, pl, pt, ru, th, tr, uk, vi, zh, zh-hant. blog.conholdate.com: ar, de, es, fa, fr, id, it, ja, ko, nl, pl, pt, ru, th, tr, vi, zh. GA4: aspose.com 252213002, groupdocs.com 252384535, conholdate.com 252867297. Small checks on .com are fine (SK). Checked 2026-10-22: all three live sitemap indexes list exactly these languages; repo completeness (local clones; groupdocs.com and conholdate.com last pulled 2026-10-09): aspose.com 6,432 posts (2,420 complete, 3,977 English only, **35 partial**, old 2013-2019 posts with 6-10 languages), groupdocs.com 1,174 (477 / 696 / **1 partial**: `signature/2026-09-10-signing-documents-linux-container-fonts-nodejs` misses fr; SK no longer translates blog.groupdocs.com, he did earlier, so this is not his agent's current work), conholdate.com 548 (547 complete, 1 English only).
- Queue after priority 4: re-check remaining seed findings (typo/spelling check on titles and H1s), LangGraph run, scheduled runs in GitHub Actions with a new/resolved digest, report to a private domain.

## Current phase: 1, AUDIT ONLY

Hard rules until SK explicitly opens Phase 2:

- Do NOT fix, change or write anything on a target site. No PRs or pushes to site repos, no WordPress or Discourse writes, no robots, sitemap or redirect edits.
- Use read-only credentials only: GSC Restricted, GA4 Viewer, read-only repo tokens.
- Do not build or mount write-capable tools yet. Fixer MCP servers belong to Phase 2.
- In this repo: do not commit or push unless SK asks.
- Crawl politely: respect robots.txt, rate-limit, send an identifiable user agent. Functional checks use small synthetic test files at low frequency.
- Out of scope: QA and staging hosts (`*-qa.*`). Do not crawl or check them.

The only output of Phase 1 is a health report made of findings (schema below).

## Operating loop

Discover → Audit → Diagnose → Prioritize → Fix → Verify → Monitor

Phase 1 covers Discover, Audit, Diagnose and Prioritize. Fix and Verify are Phase 2.

## Architecture (confirmed by SK, 2026-10-08)

```
core/         deterministic logic: crawl, parse, validate, score, findings store
mcp_servers/  MCP servers, thin wrappers over core (agent-facing). Not `mcp/`: that name would shadow the `mcp` SDK package
api/          REST, thin wrapper over core (dashboard, CI), later
agents/       LLM agents; they call MCP tools only
tenants/      one YAML per property (aspose.app, conholdate.cloud, aspose.cloud, groupdocs.cloud); `property` must equal the file name
scripts/      one-off CLIs (e.g. check_access.py)
reports/      reports/<tenant>/: generated reports, committed (run JSON, report HTML, notes, findings.json, archive/)
data/         data/<tenant>/: SQLite stores and caches, gitignored
```

- **Deterministic checks are code, not LLM calls.** Status codes, redirects, canonicals, hreflang, schema validation and Core Web Vitals must be reproducible and cheap.
- **LLM agents only where judgment is needed:** content correctness, root-cause diagnosis, prioritization, and later writing fixes.
- **Read and write live in separate MCP servers,** so Phase 1 cannot write even by accident.

| MCP server | Phase | Access |
|---|---|---|
| `gsc`, `ga4`, `crawl`, `pagespeed`, `findings` | 1 | read-only (`findings` writes only to our own store) |
| `fix-git`, `fix-wordpress`, `fix-discourse` | 2 | write, not built yet |

Stack (confirmed):

| Piece | Role |
|---|---|
| Python | One language for crawlers, Google APIs, MCP servers and agents |
| MCP Python SDK (`mcp` 2.x, `MCPServer`; FastMCP was renamed in 2.x) | Our MCP servers; stdio transport locally, streamable HTTP later |
| `googleanalytics/google-analytics-mcp` | Google's GA4 server (experimental, read-only); reuse it or wrap the same API ourselves |
| Own `gsc` server | Thin wrapper over the Search Console API, `webmasters.readonly` scope |
| LangGraph | Orchestrates the audit run as a graph: fan out auditors, retry, checkpoint, resume, human pause |
| `langchain-mcp-adapters` | Lets LangGraph agents call our MCP servers; Claude Code calls the same servers directly |
| SQLite → PostgreSQL | Findings store: SQLite file for the pilot, PostgreSQL when multi-tenant, scheduled or shared |

**Architecture diagram (2026-10-11):** source of truth is `docs/architecture/site-health-architecture.html` (hand-drawn inline SVG data-flow diagram + run table, design rules, code layout), snapshot `docs/architecture/site-health-architecture.png` (shown in README). Published privately at https://claude.ai/artifact/3zrEcbrV1WxN9nfjvS7Kxm. SK: keep the diagram in its current shape; when the architecture changes, edit that file (dashed = planned, solid = built), re-render the PNG, and republish to the same artifact URL.

## Where things run

Everything runs on SK's Mac (macOS) from VS Code / Claude Code, which has normal network access to aspose.app and Google APIs. (The earlier claude.ai cloud session could not reach aspose.app; that is why development moved here.)

- Repo: `/Users/Apple/Work/Aspose/GitHub/aspose.app-health-and-recovery/site-health-and-recovery` (remotes: `origin` = GitLab `gitlab.recruitize.ai/.../site-health-and-recovery`, upstream of `master`; `github` = GitHub `shoaibkhan-aspose/health-and-recovery` (**public**; Pages via GitHub Actions, Settings → Pages → Source: GitHub Actions), added 2026-10-08. Push to each explicitly: `git push origin master`, `git push github master`).
- Parent folder `/Users/Apple/Work/Aspose/GitHub/aspose.app-health-and-recovery` also has empty `docs/` and `ClaudeChat/`.
- products.aspose.app source (read-only): `/Users/Apple/Work/Aspose/GitHub/aspose-app/products.aspose.app`.
- **Standalone project (SK, 2026-10-08):** do not integrate with `conholdate/blog-team-tools` or its dashboard for now. Everything, including reports and any UI, is built here.
- **Sharing reports:** two outlets: a private claude.ai Artifact (link shared at SK's discretion), and **GitHub Pages**: `.github/workflows/pages.yml` runs `scripts/build_site.py` on every push to `master` (installs PyYAML; reads only committed files: `reports/<tenant>/findings.json`, run JSONs, traffic summaries and archives, since `data/` is not in git) and deploys the landing page, one report per tenant, one page per host, the archives and the fix guide to https://shoaibkhan-aspose.github.io/health-and-recovery/. Audits run on the Mac and must commit their run JSON, `reports/<tenant>/findings.json` and the traffic summary. The repo is **public**; never commit key material, tokens or anything SK marks confidential. Pages stay `noindex, nofollow`; traffic numbers are published as is until the move to a private domain (SK, 2026-10-20: soon).
- **Claude Code MCP approval:** `gsc` is pre-approved in the workspace folder's `.claude/settings.local.json` (`enabledMcpjsonServers`), personal and outside git.

## Status (2026-10-08..20)

Done:
- Brief, stack and layout confirmed by SK.
- Scaffold: `pyproject.toml`, `.gitignore` (keys, `.env`, `reports/`), `.env.example`, `README.md`.
- `core/tenant.py` (load + validate tenant YAML, `is_excluded()` for QA hosts), `core/google_auth.py` (ADC from `GOOGLE_APPLICATION_CREDENTIALS`, refuses non-`.readonly` scopes), `core/gsc.py` (sites, searchanalytics, sitemaps; 3-day lag window), `core/ga4.py` (runReport).
- `scripts/check_access.py`: read-only check of GSC properties (permission, 28-day clicks/impressions, top pages, sitemap errors) and GA4 (sessions + organic sessions per hostName). Writes `reports/access-check-<date>.json`; exit 1 if any check fails.
- `tenants/aspose.app.yaml`: hosts, GSC properties, GA4 ID, 29 product families, GSC sitemaps snapshot (38 entries).
- `tests/test_foundation.py`: 8 offline tests with fake clients. Pass; `ruff check .` clean.

- `.venv` set up with `pip install -e ".[dev]"`; `.env` holds the key path (quoted: the path contains a space). Load it with `set -a; source .env; set +a` (scripts do not read `.env` themselves).
- **`check_access.py` run 2026-10-08** (report `reports/access-check-2026-10-08.json`, exit 1 because of GSC gaps). Identity: `sk-service-acc@aspose-app-health-and-recovery.iam.gserviceaccount.com`.
  - GSC (window 2026-09-08..2026-10-05): **only `https://products.aspose.app/` is readable** (`siteRestrictedUser`): 1,629,131 clicks, 23,994,949 impressions; 38 sitemaps, 6 with errors (`/gis/sitemaps/sitemap.xml`, `/omr/sitemap-percentage.xml`, `/omr/sitemap.xml`, `/video-app/sitemap.xml`, `/drawing/sitemap.xml`, root `/sitemap.xml`), matching the GSC UI snapshot. Top pages are barcode locale pages (`/barcode/fa/recognize/qr` 49k clicks, `/barcode/ar/recognize` 49k, `/barcode/ru/recognize/qr` 36k, `/barcode/fa/scan` 33k) and `/pdf/merger/jpg-to-jpg` (31k clicks, 692k impr).
  - about, blog, releases, websites: not visible on the first run; SK added the service account, and the **re-run (2026-10-08) passes, exit 0**. 28-day clicks / impressions / submitted sitemaps: about 15 / 2,306 / 0; blog 154 / 57,088 / 1; releases 6 / 570 / 0; websites 2 / 729 / 1. No sitemap errors. about and releases have **no sitemap submitted** (candidate finding).
  - GSC clicks are far below GA4 organic sessions on small hosts (about 15 vs 2,263; websites 2 vs 594; blog 154 vs 443). GA4 "Organic Search" includes Bing and other engines, but gaps this size suggest misattribution. Investigate before using GA4 organic for prioritization.
  - GA4 `253117495` readable. One property covers all subdomains. Sessions / organic over 28 days: products 2,712,015 / 1,769,580; (empty hostName) 241,398 / 204,923; purchase 9,447 / 7,616; www 8,707 / 4,366; forum 7,545 / 387; dashboard 5,152 / 3,670; about 3,917 / 2,263; blog 2,061 / 443; websites 1,286 / 594; metrics 407 / 51; releases 279 / 12; status 95 / 36; api.products 14,998 / 80.
  - GA4 also shows noise hosts: `politesardine.info` (19,893), `sparklingcattle.com`, `aspose.test`, `about.aspose.org`, `products-aspose-app.translate.goog`, and QA hosts (`products-qa`, `slides-qa-ui-app...k8s.dynabic.com`). Likely ghost/spam or a misplaced tag; a candidate finding (data hygiene, no hostname filter).
  - Hosts not in the tenant YAML: purchase, dashboard, metrics, status, api.products. Discovery should confirm them.

- **Discovery built (2026-10-08):** `core/discovery/` (`fetch` polite GET-only fetcher with robots.txt per RFC 9309, per-host rate limit, retries; `sitemap` parser for XML/gz/BOM/plain-text; `classify` host/section/lang/template; `store` SQLite inventory; `run` orchestration + findings), `core/findings.py` (`make_finding`, schema only; store is step 3), CLI `scripts/discover.py`. Tenant YAML gained `fix_channel` per host, 5 GA4-seen hosts, `discovery.section_sitemaps` and `url_templates`. 20 offline tests pass, ruff clean. Install with `pip install -e ".[dev,crawl]"`.
  - Findings are grouped per host, or per section folder on hosts with configured sections (products), so one template fix = one finding.
  - Sample run (www + products pdf/words/omr, 80 sitemaps, ~80 s) confirmed: products robots.txt 404; root `/sitemap.xml` and both omr sitemaps 404 live (GSC: Couldn't fetch); www robots.txt has no `Sitemap:` line, www sitemaps have no lastmod; pdf language sitemaps have no hreflang; words sitemaps have full hreflang (40 langs, 19,320 URLs = GSC count) but **33 of 36 words sitemaps (14,880 URLs) carry the same lastmod 2024-02-13** (new).

- **Seed findings documented (2026-10-08):** `tenants/aspose.app.seed-findings.yaml` (29 manual findings, 11 verified, 1 note) + `tests/test_seed_findings.py`. See section Seed findings. Reviewed by Claude Code the same day: crawl-02 and intl-04 verified from discovery data; crawl-03 and content-03 half-confirmed (sitemap side); intl-05 rewritten (websites sitemaps have 38 uneven languages, not 6); fix channels aligned to `FIX_CHANNELS`; seed-crawl-01 turned into a note on the discovery robots finding.
- **Findings store built (2026-10-08):** `FindingsStore` in `core/findings.py` (`data/findings.sqlite`, gitignored). Stable key per finding (`<dimension>/<check>/<subdomain>/<template>` for code findings, `seed/<id>` for seeds) → one permanent id (`crawl-0001`, seeds keep `seed-…`). Tracks first/last seen run, resolves findings a later run no longer reports (only within that run's hosts/sections; a run stopped by `--max-sitemaps` resolves nothing), reopens them if they return, keeps an event log (new/resolved/reopened per run), attaches seed `notes` to findings by key. `discover.py` imports the seed file and its run automatically; `scripts/findings.py` (`import-seed`, `import-discovery`, `list`, `summary`, `export` → `reports/findings.json`, also written by every `discover.py` run); `build_report.py` reads findings from the store (source filter, unverified and new tags, notes, resolved list). Discovery findings now carry a `check` name. 27 offline tests pass.

- **Crawl auditor built (2026-10-08, step 5):** `core/audit/` (`sample` stable hash-ranked sample per (host, section, template) from the inventory: 2 default-language pages + 1 page in each of 2 other languages; `page` lexbor parser for title, meta description, H1, canonical (head + `Link` header), robots meta + `X-Robots-Tag`, hreflang, html lang, viewport, meta refresh; `crawl` per-page checks + duplicate title/description per host and language → findings grouped per host or products section, template `page` / `page:<section>`, `affected_pages` extrapolated from the sampled share; `store` `data/audit.sqlite`). CLI `scripts/audit_crawl.py`; source `crawl-audit` in the findings store (`scripts/findings.py import-audit`). Fetcher now keeps response headers and redirect hop statuses. 31 checks in `CHECKS` (crawl, onpage, intl, ux); 33 since 2026-10-16 (2 `ai` page checks). Tenant YAML gained `audit:` (`per_template_by_host` forum 20, `section_urls` for the products hubs, `extra_urls` pdf split/splitter). `--sections` narrows only products: other hosts and every homepage are always audited, and their findings can resolve (`import_run(resolve_unsectioned=True)`). Hosts are fetched round-robin, so per-host rate limits overlap. 46 offline tests pass.
  - **Run 4** (2026-10-08, SK chose products **barcode + html only** plus all other hosts; 118 pages, 75 s): 58 findings. Report `reports/crawl-audit-2026-10-08-run4.json` (runs 1-3 were tuning runs, deleted). Headlines:
    - **forum: 20 of 20 sampled topic URLs from the sitemap return 403** ("private") for every user agent incl. Googlebot's; the sitemap lists 41,894 topics.
    - **html** app pages: hreflang lists every language **except the page itself** (English pages have only `x-default` pointing to them, no `en`); conversion templates emit canonical + hreflang **twice**.
    - **barcode** app pages: hreflang without `x-default`. barcode and html **hubs have no hreflang** (seed-intl-02 reproduced).
    - pdf/barcode/html app pages **do** have hreflang in raw HTML: **seed-intl-01 not reproduced** for these families.
    - releases: sampled release-notes pages are `noindex, nofollow` yet listed in the sitemap; no canonical, no html lang, no meta description. websites: 3 of 12 sampled sitemap URLs are meta-refresh stubs (`/en/`, `/fileformat/`), `<html lang=en>` on `/ko/`, `/nl/`, ... pages. metrics, www, websites: localized pages with no hreflang in HTML. status: duplicate titles/descriptions, `/dashboard` in sitemap 302-chains to an SSO login. user-scalable=no on blog, releases, status, websites. api.products homepage 404.
  - Not yet covered: products families other than barcode/html (SK to decide when); canonical-target and hreflang return-link fetches; spelling/typo checks on titles (seed-onpage-01..04 need a dictionary or LLM check).

- **Prioritizer built (2026-10-09, priority 1):** `core/prioritize.py` + `scripts/prioritize.py`. Fetches GSC page rows per property (28 days, paged 25k, max 200k/property; products 19,114 pages) and GA4 organic sessions per host, cached in `data/traffic-<tenant>-<window>.json` (`--offline` reuses it). Classifies GSC pages into the findings' (host, section, template) buckets. Share at stake: crawl audit = template traffic x failing share of the sample (`evidence.sample`, new); discovery = section/host traffic x affected_pages / section URLs (inventory), whole scope for robots/no-sitemap checks, and a failed sitemap file only the URLs GSC discovered from it (tenant snapshot), else 0; seeds = their exact URLs. Hosts without a GSC property use GA4 organic sessions. `score = min(100, 20*log10(1 + clicks + 0.01*impressions)) x severity (broken 1, incorrect .7, not_optimized .4, improvable .2) / effort (S 1, M 1.5, L 2.5)`. Writes `impact` (clicks_28d, impressions_28d, score, source, share, window) into the store (`set_impacts`; re-imports keep it) and re-exports findings.json. Run it after every discovery/audit import. Report: "Top priorities" (top 10) and score + traffic on every finding. 50 offline tests.
  - First run (GSC 2026-09-09..10-06): top = omr no working sitemap (89; 13k clicks, 1.6M impressions), slides double-slash sitemap (83), html hreflang without self (63), purchase robots.txt is HTML (54), forum private topics (52).

- **Priority 2, crawl audit of all products families (2026-10-09):** batches by GSC traffic: run 6 = words, cells, pdf, imaging, omr; run 7 = 3d, zip, audio, email, gis, video, total, slides; run 8 = the 14 smallest. New: sections with no sitemap URLs (omr, drawing) are sampled from their top GSC pages (`search_pages` from the traffic cache, source `search`). Tenant `audit.ignore_pages` skips pages (no findings, not in the sample); forum private topics (403 under `/t/`) are ignored per SK, which resolved the forum HTTP-error finding.
  - **cells canonical bug (verified with URL Inspection):** 22 of 26 sampled cells pages declare a canonical without `/cells` (`/cells/conversion/xls` → `https://products.aspose.app/conversion`, also `/form`, `/merger`, `/clear`, ...). Google overrides it on strong pages (xls indexed under its own URL) but drops others as "Alternate page with proper canonical tag" (`/cells/form/to-do-list/xlsx`, `/cells/remove-watermark` folded into `/cells/clear/csv-to-ots`). At the May crawl `/cells/conversion/xltm-to-zip` still had a self canonical, so the bug is recent (May..Oct 2026). Fix: the cells app must build canonicals with its base path.
  - Run 8 (14 smallest families): **cad and psd translated pages canonicalize to the English page** (`/cad/tr/conversion/fbx-to-3ds` → `/cad/conversion/fbx-to-3ds`), cancelling their hreflang; ocr conversion pages canonicalize to `/ocr/conversion`. "hreflang omits the page itself" appears in 14 families (one shared component likely). One-off 500/502/503 on some cad hubs, ocr and drawing pages: re-check next run.
  - **Evidence locations (2026-10-09):** findings carry `evidence.locations` [{role, url, note}]: page, listed in (sitemap from the inventory), sitemap index, canonical target (fetched once, status shown; max 50/run); discovery double-slash findings lead with the sitemap index. All cells canonical targets return 404. Discovery run 8 + full crawl audit run 9 (652 pages, 198 findings, all reproduced; batch files runs 5-8 deleted). cad 500, ocr 502, drawing 503 repeated in run 9.
  - Totals after runs 5-8: 652 pages audited, 312 open findings, all scored. The report merges every crawl-audit run (newest result wins per page; `build_report.py --audit` takes a comma list); `summarize_pages` in `core/audit/crawl.py`.
  - words hubs (`/words/`, `/words/family/` and locales) have hreflang but no canonical; the sitemap lists them without the trailing slash (301). `/pdf/splitter` → `/pdf/split` via two 301s (seed-crawl-03). omr app pages: two H1s, hreflang without self. imaging: meta descriptions too long on most templates.

- **Family scorecards (2026-10-09, SK):** families have (almost) separate teams, so a traffic-only score makes small families' issues look unimportant. Two separate measures now: **health** (A-F, traffic-free) for the team and **traffic** for the business. `core/scorecard.py`: each open finding costs broken 40 / incorrect 20 / not_optimized 6 / improvable 2 x share of the family (crawl sample share, discovery impact share, else pages/URLs; min 0.25); root-cause groups count once (sitemap, page errors, canonical, hreflang, redirects, titles, ...; http_error on `//` URLs joins the sitemap group); cosmetic total capped at 20; a canonical whose target is 4xx/5xx counts as broken. Grades A>=90 B>=75 C>=60 D>=40 F. Top 3 per family, blockers (broken) first. Cards for **products families only, no owner** (SK). `prioritize.py` also fetches the previous 28 days and the same window six months earlier and writes the committed `reports/traffic-summary.json`; the report shows clicks now vs previous vs six months ago. First grades: drawing F 20 (569 → 10 clicks vs six months ago), omr F 38 (28k → 13k), cells D 47, slides D 48; 13 families at C (hreflang without self); words, pdf, imaging, audio, video, diagram, barcode, ebook, email at B. Report: "Product families" section after Summary (default A to Z per SK 2026-10-12; 12 shown; sorts: lowest/highest health, most/least traffic, drop/gain vs six months and vs previous 28 days; the extremes strip was removed per SK) and a Family filter on findings.

- **Sitemaps per family in the report (2026-10-12):** discovery reports now carry `sitemaps` ({host: {section: [url, parent, depth, status, kind, urls (recursive), children, ok, error, corrected]}}): sitemaps that work or were published (robots, GSC, listed by an index); failed guesses are left out; `corrected` = a double-slash child we fetched with one slash, not listed by the index. Run 8 was backfilled from the inventory. Card status "Sitemap" opens the family's files (index first, then children; 8 shown, then "Show all"); the Submitted sitemaps table links each path. Grade bands: the letter is the health number in bands (A 90+, B 75-89, C 60-74, D 40-59, F <40); SK asked about it, explained, no change yet.

- **Family cards layout (2026-10-12):** Rows (default: one family per row, three zones identity / traffic / work, grade-colour left stripe; zones stack at <960px and <600px) or Grid (compact cards), switch remembered per viewer. Global `[hidden]{display:none!important}` in the template fixed closed sitemap panels showing as empty bars.

- **Readable finding details (2026-10-12):** Observed shows the sample as a Template / Failed / Sampled table (worst first, `generic:` buckets as `/fam/…/…`) plus the estimate explained; findings without a sample list observations as bullets (split before each URL); Evidence shows short paths and "canonical →"; Impact is a labelled table (priority score, traffic at stake with the GSC window, severity, fix effort S/M/L spelled out). Effort meaning: S = one template or config change, M = several templates or translations, L = rebuild or migration.

- **Speed auditor (2026-10-15, priority 3):** `core/pagespeed.py` (PSI v5 client: retries on 429/5xx; a Lighthouse "cannot load" answer raises `PageLoadError` (a result about the page), other failures `PageSpeedError` (not measured); `extract()` keeps URL field data (None when PSI falls back to origin), origin field data, lab score/metrics, top 3 Lighthouse savings), `core/audit/perf.py` (`select_pages`: per crawl-audit group the 2 pages with most GSC clicks from clean HTML 200 crawl pages + GSC pages of the same group; 353 pages / 206 groups / 11 hosts, `--plan` lists them), CLI `scripts/audit_perf.py` (mobile, 4 parallel, ~40 min with retries, report `reports/perf-audit-<date>-run<id>.json`, source `perf-audit`). Pages that fail are retried once at the end; only a second failure counts.
  - Checks (dimension `perf`): `lcp/inp/cls_poor` (not_optimized), `lcp/inp/cls_needs_work` (improvable), `ttfb_poor` (not_optimized), `lab_load_failed` (broken: server error, timeout, not HTML, twice; scorecard group "page errors"), `lab_no_paint` (incorrect: page loads but paints nothing in Google's mobile test, twice; e.g. JS-only shells), host-level `origin_cwv_poor` / `origin_cwv_needs_work` (template `origin`, whole-scope in the prioritizer). Real-user checks use CrUX p75 over 28 days and Google's thresholds; pages without URL-level data count neither way. A run with >10% API errors (after retry) is `incomplete` and resolves nothing.
  - **Lab score is information only (SK, 2026-10-15):** it moved by a median 4 and p90 19 points between two runs of the same pages, so "score below 50" findings flipped every run. It stays in finding notes ("lab 6.1 s, lab score 42; biggest savings: ...") and in the report's Reference table "Speed per host" (whole-host LCP/INP/CLS, pages, real-user coverage, not loaded, median lab score).
  - Wiring: fix guide area "Speed", scorecard group `speed` (counts once per family, cosmetic cap applies), report label "Speed audit", method text, footer, run changes and health-history label. Tests in `tests/test_perf_audit.py`.
  - **Auth:** PSI works with the service account (identity-only `openid` scope, allowed by `assert_readonly`); SK enabled the API in project `629629479690` on 2026-10-15 (old account); since 2026-10-20 the new account in project `health-and-recovery` (385867072171) is used and PSI works there too. `PAGESPEED_API_KEY` in `.env` also works. The keyless quota is shared and exhausted. The CrUX API itself rejects service-account tokens (needs an API key); only needed later for CrUX history (trends).
  - First findings (tuning runs 10-11, 2026-10-15): **ocr app pages fail** (8 of 8 sampled: HTTP 500 or ~22 s to first byte, confirmed with curl); websites `/fr/groupdocs/`-type pages paint nothing (JS shell); cells CLS 0.12-0.13 on 8 of 9 pages with data; barcode CLS > 0.25 and INP > 500 ms; gis LCP > 4 s; INP 200-500 ms on pdf, video, font, omr; dashboard host LCP 3.3 s. Whole-host data passes on products, www, about, purchase, websites, forum. Tuning runs were removed from the findings store (backup in the session scratchpad) before the first real run.
  - **First real run: speed audit run 12 (2026-10-15):** 353 pages, 15 findings, scored with the cached traffic window (`prioritize.py --offline`). Top: barcode CLS > 0.25 (#35, score 40, 81k clicks) and INP > 500 ms; cells CLS 0.1-0.25 (202k clicks); gis LCP > 4 s (gis health 64 -> 58, C -> D). ocr loaded for Google in this run, but curl still got HTTP 500 on 2 of 3 ocr pages afterwards: **ocr is intermittently failing**; the next crawl audit (http_error) should confirm it. Report rebuilt with the Reference table "Speed per host"; archive now holds 2026-10-12, 2026-10-15 (restructured report, before the speed audit; downloaded from Pages, byte-identical to a build of the last commit) and 2026-10-15-2 (after the speed audit). Architecture diagram updated (step 3 audit_perf, PageSpeed source, steps renumbered 1-6 in the run table), PNG re-rendered, artifact republished (version 3).
  - Still to do: consider a "Speed" status on family cards (discuss with SK).

- **AI-readiness auditor (2026-10-16, priority 3; scope agreed with SK 2026-10-15):** deterministic v1, dimension `ai`, scorecard group `ai` (counts once per family, cosmetic cap), fix-guide area "AI readiness", report Reference table "AI access per host", source label "AI audit".
  - Host checks: `core/audit/ai.py` + `scripts/audit_ai.py` (source `ai-audit`, report `reports/ai-audit-<date>-run<id>.json`, ~5 min, ~190 requests). robots.txt evaluated per RFC 9309 (own parser: most specific group, longest match, allow wins ties; `urllib.robotparser` gets both wrong) for AI *answer* bots (OAI-SearchBot, ChatGPT-User, PerplexityBot, Perplexity-User, Claude-SearchBot, Claude-User, Googlebot, Bingbot) on `/` and every section root: `ai_bot_blocked` (broken). *Training* bots (GPTBot, ClaudeBot, CCBot, Google-Extended, Applebot-Extended, meta-externalagent, Bytespider) are information only (SK). Firewall probe: homepage once per bot user agent (audit name appended), 403/challenge/<50% size = `ai_bot_firewalled` (broken; answer bots only); a CDN verifying bot IPs may block only our imitation, the fix guide says to confirm in CDN logs. llms.txt: `/llms.txt` per host (tenant `audit.ai.llms_txt_skip_hosts`: dashboard, api.products) and `/<section>/llms.txt` per family; only a real text file can be `llms_txt_invalid` (incorrect: empty, no H1, no links, or up to 10 checked links fail); an error status, redirect or HTML page is `llms_txt_missing` (improvable), because family apps redirect unknown URLs to app/error pages (16 families did; the first tuning run wrongly called those "invalid" and was removed from the store, backup in that session's scratchpad). While a host has no usable llms.txt there is one host finding listing the families without their own file; family findings (`llms.txt:<family>`) appear only once a host file exists and does not link the family.
  - Page checks in the crawl auditor (no extra requests): `PageFacts.text_chars` (visible body text without script/style/nav/header/footer, no spaces) and `jsonld_types`/`jsonld_invalid`. `content_needs_js` (incorrect) below 250 characters; `no_structured_data` (improvable) when no JSON-LD parses. Both skip noindex pages. Fetcher `get()` now takes per-request headers.
  - Prioritizer: the four host checks are whole-scope. `seed-ai-01` superseded by ai-0004.
  - **Results (AI audit run 16 + crawl audit run 15, 2026-10-16):** no host blocks AI crawlers (robots.txt names none; BunnyCDN answers all bot user agents normally). No llms.txt on 9 hosts (only about has one; products has only `/pdf/llms.txt`). Almost no text without JavaScript: websites JS shells (`/fr/groupdocs/` 34 characters), purchase and dashboard homepages, and short status pages (incident pages are server-rendered but one line long: the fix guide names both causes). No JSON-LD: about, www, releases, status, websites, purchase, dashboard and products diagram (11.6k pages est.), words, psd, finance, ebook. Family health moved 1-2 points in 5 families (words, diagram, finance, psd, ebook).
  - Report built from findings store vs CI export differs only in `notes: []` vs `null` on one resolved finding in "Changes" (invisible; pre-existing).

- **Text check (2026-10-20, SK chose it before priority 4):** first LLM use. `core/llm.py` (OpenAI-compatible client from `PROFESSIONALIZE_API_KEY` / `_BASE_URL` / `_LLM_MODEL`, model `gpt-oss`; up to 4 calls at once, all calls pause 30 s after a failure: SK wants normal speed, polite only on trouble), `core/audit/text.py` + `scripts/audit_text.py` (source `text-audit`, report `reports/text-audit-<date>-run<id>.json`, ~5 min uncached, 31 calls of 20 pages). Reads the crawl-audit pages (newest per URL; no requests to the site), sends path, language, title, H1, description; checks `text_typo` (misspelling, repeated word, leftover/placeholder or garbled word) `text_leftover` (template keys such as CADWatermarkTitle2, test words, garbled/untranslated words) and `text_topic_mismatch` (title/description names a different specific product than path + H1); dimension `onpage`; typo `improvable`, leftover and topic `incorrect` (SK, 2026-10-20); scorecard group `wording`, fix-guide area "Spelling & wording". Guards: an answer is kept only if its wrong text occurs in that field; digits-only and H1-shared topics dropped; answers cached per page text in `data/text-check-cache.json` keyed by prompt version + model (rerun on unchanged text = same result, no calls); runs with >10% unchecked pages resolve nothing; reviewed false positives in tenant `audit.text.ignore` (url, optional wrong). Prioritizer scores these on the exact pages (like seeds, `EXACT_PAGE_SOURCES`).
  - Tuning: prompt v1 gave ~81 issues, ~30 false positives (generic titles called "different product", units, years, grammar). Prompt v2 + filters: 59 issues, 14 false positives, now in `audit.text.ignore`. Tuning runs 18 and 19 were removed from the findings store (backup in that session's scratchpad); **run 21 is the first real run**: 25 findings (onpage-0099..0123), 605 pages checked (runs 18-20 were tuning and severity changes; removed from the store, JSONs deleted). Run 23 (same day, from cache) dropped onpage-0110: the /total/compress/tga description lists PDF/Excel/PowerPoint/Word, which is right for Aspose.Total (the bundle of all Aspose products, SK) and is now a reviewed exception; the finding was deleted from the store, not resolved. Tried first: a per-section note for the LLM ('Total = all products'); it made the model flag 3 generic Total titles instead of 1, so it was dropped (run 22 removed).
  - Real finds: template keys live on CAD watermark pages (`CADWatermarkTitle2`, `CADWatermarkMetaDescription2` as title/H1/description); audio converters described as "Visio" files (de, ja); tasks merger descriptions say MPP->PDF on XML/MPX/PDF pages; TGA compressor described as PDF/Word/Excel; typos iamges, simular, onlien, Onete, Image image, MergeEPS/MergePS, OTFfile, KonverterWAV; a Cyrillic "С" in "Сonvert" (/pub/applications); garbled translations (hu "nak nek", cs "Flouze", fa "To", zh-cn "compress"); /email/conversion/eml title is just "apps"; a soft 404 (see Next session). Seeds onpage-01, 02, 04 superseded by onpage-0103, 0108, 0116; seed-onpage-03 narrowed to the /finance/family/ "APIs" title (the typos are onpage-0113).
  - Architecture diagram: Internal LLM source and step 5 audit_text.py added (prioritize is 6), PNG re-rendered with headless Chrome (1280x1130), artifact version 5.
  - Health: a family with a leftover or wrong-product finding loses 5 (incorrect x min share 0.25); a plain typo costs 0.5 (cosmetic, capped with the others).

- **Multi-tenant, host health, host pages, rename (2026-10-20, second half of the day):**
  - **Multi-tenant layout (SK: one subfolder per tenant):** tenant 2 `conholdate.cloud` (only blog.conholdate.cloud) added and run once; every tenant's files live in `data/<tenant>/` (gitignored) and `reports/<tenant>/` (committed; `core/paths.py`); all scripts take `--tenant` / `TENANT` (default aspose.app); `scripts/build_site.py` builds the Pages site (landing page at `/`, report at `/<tenant>/`, archive at `/<tenant>/archive/`, redirects from the old `/#…` and `/archive/<date>/` links to `/aspose.app/`); the workflow runs it (installs PyYAML). New service account `sk-serv-acc@health-and-recovery` used for every tenant (see "Open discussions", tenant 2). The aspose.app report built at `/aspose.app/` was byte-identical to the live page before the move.
  - **Host health and shared fix guide (2026-10-20, SK):** every host without product families gets a health card (same score as families: `core/scorecard.scorecard`, scope = whole host; `build_report.add_hosts`; section "Host health"); `prioritize.py` writes `host_totals` (GSC clicks per host, or GA4 organic sessions) into the traffic summary. blog.conholdate.cloud scores **B 86** (ai -7.5 for no text without JavaScript on listing/category pages, hreflang -2, headings -2, descriptions -1.2, titles -1.2). aspose.app hosts: about A 90, forum A 92, blog B 86, metrics B 85, www B 75, dashboard C 62, releases C 60, status C 67, api.products D 52, purchase D 46, websites D 48. The fix guide is one shared page at `/fix-guide/` (`build_site.guide_page`, anchors `#g-<check>`, "Open findings" per report); published reports pass `--guide-url ../fix-guide/` and show only a list of their checks with links; snapshots link `../../../fix-guide/`; local builds keep the full table. Text check run 4 for conholdate.cloud (SK allowed the borrowed LLM key for blog text): 15 pages, no findings. Known nuance: a crawl finding's share is failed/sampled over the templates where it failed, so a homepage-only problem counts as the whole host (e.g. blog h1 -2 instead of ~-0.5).
  - **Pages URL rename done (SK renamed the repo, 2026-10-20):** GitHub repo `shoaibkhan-aspose/health-and-recovery`, Pages https://shoaibkhan-aspose.github.io/health-and-recovery/<tenant>/; `github` remote and links updated. Old `/aspose-app-health-and-recovery/...` Pages links now 404 (GitHub forwards git and repo URLs, not Pages). Old links keep working through the redirect repo `aspose-app-health-and-recovery` (see Report layout changes below).
  - **Report layout changes (SK, 2026-10-20, later):** published reports no longer show a Fix guide section at all (every finding already links "How to fix →" to the shared page; the menu and the All findings intro link there too); host health is a table, one host per row (health with points lost on hover, open findings + "See N →", search traffic, URLs, biggest issue), not cards. Family cards unchanged. **products.aspose.app has a row too** (SK noticed it was missing): `build_report.family_rollup` = families' health weighted by search clicks (72) minus host-wide findings that belong to no family (-16: root /sitemap.xml unreachable, empty video-app sitemap, no robots.txt, no llms.txt, ...) = **D 56**; the row names the lowest family (/drawing/ F 19) because an average hides it. Before this, those 7 host-wide products findings counted in no grade at all.
  - **Host pages (SK, 2026-10-20; SK chose flat URLs over nested):** every host has a page at the site root, `/<host>/` (e.g. `/blog.conholdate.cloud/`, `/forum.aspose.app/`): the tenant report filtered to that host (`build_report --host`, `focus_host`): its findings, changes, reference rows, pages audited, and family cards for products.aspose.app; scores identical to the tenant page. Header: Property + Host dropdowns ("All hosts" = tenant page); the tenant's host table links to the host pages; landing lists hosts; "Previous versions" on a host page = the tenant archive (no per-host snapshots; `--host` with `--snapshot` is refused). `build_site.site_hosts` stops the build if a host name equals a tenant or a site folder (`fix-guide`, `archive`): the reason nesting was recommended. Apex domains are not separate sites (checked 2026-10-20: aspose.app and aspose.com 301 to their www host; SK: www counts as the homepage), so the tenant/host clash does not occur today; the check stays as a guard. Per-family pages (e.g. `/products.aspose.app/pdf/`): SK, 2026-10-20: later.
  - **Property switch (SK, 2026-10-20):** published reports have a "Property" dropdown and an "All reports" link at the top; switching keeps the #section (`build_report --site-tenants`, passed by build_site.py). Local pages and snapshots have no switch. A small layout change, so no snapshot was taken for it.
  - **Bug fixed (SK spotted, 2026-10-20):** the Host health section had `id="hosts"`, the same id as the Reference table "Hosts: robots.txt and sitemaps", so the Hosts, Sections and Submitted sitemaps tables rendered empty from snapshot 2026-10-20-3 until the fix (section is now `id="host-health"`; a test rejects duplicate ids in the template). conholdate.cloud has no `gsc_sitemaps_snapshot`, so its Submitted sitemaps table now says so instead of staying empty. Idea for later: read submitted sitemaps live from the GSC API (`core/gsc.py` already lists sitemaps) instead of a hand-pasted snapshot. Archive gap closed: conholdate.cloud versions 2026-10-20-3 (rebuilt from commit c63dbbf) and -4 (downloaded) added; keep archiving every tenant's live page before each push, not only aspose.app.
  - **api.products.aspose.app (SK, 2026-10-20: "cannot find this domain"):** it resolves (CNAME aspose-app.lb.k8s.dynabic.com) and GA4 counts ~11.6k sessions/28 days, but `/` answers 404 S3 NoSuchBucket: an API/backend host, not a website. It is in the tenant YAML only because GA4 showed it (2026-10-08, "not yet confirmed by SK"). **Dropped (SK agreed, 2026-10-20):** removed from the tenant hosts and `llms_txt_skip_hosts`; its 3 findings (crawl-0010, crawl-0057, crawl-0071) and their observations/events deleted from the store (backup in that session's scratchpad), 367 findings left. Run files still list it; `build_report.drop_hosts` leaves out hosts no longer in the tenant YAML (host table, crawl/AI/speed/text summaries). aspose.app now has 11 hosts.
  - **Redirect repo (2026-10-20):** SK created the public repo `shoaibkhan-aspose/aspose-app-health-and-recovery`; local clone `/Users/Apple/Work/Aspose/GitHub/aspose-app-health-and-recovery-redirect` holds `index.html` = `404.html` (JS keeps path, query, #anchor; old root and /archive/ go to /aspose.app/), `.nojekyll`, README. Pushed; SK enabled Pages (Deploy from a branch, main, / (root)) the same day. Verified in headless Chrome: old root and `/#findings` -> aspose.app report, `/archive/2026-10-12/` and `/archive/` -> aspose.app archive, `/conholdate.cloud/` and `/fix-guide/` -> same pages on the new site.

Not done yet:
- GSC properties for www and forum (none exist or none shared; the service account sees only the 5 URL-prefix properties).
- `agents/` is an empty package. MCP servers still to build: `findings`, `ga4`, `crawl`, `pagespeed`.

## Working in this repo

```bash
python3 --version                      # needs 3.11+
python3 -m venv .venv && source .venv/bin/activate
pip install -e ".[dev,crawl,llm]"      # extras: mcp, agents, crawl, llm (openai client for the text check)
pytest                                 # offline, no network or keys needed
ruff check .
set -a; source .env; set +a            # loads GOOGLE_APPLICATION_CREDENTIALS (key outside the repo)
python scripts/check_access.py --tenant aspose.app
python scripts/discover.py             # all hosts; --hosts/--sections/--max-sitemaps for samples
python scripts/audit_crawl.py --sections barcode,html   # crawl audit; --sections narrows products only
python scripts/audit_ai.py             # AI readiness: AI crawler access, llms.txt per host + family
python scripts/audit_text.py --plan   # text check: pages, cached answers, LLM calls it would make (needs PROFESSIONALIZE_* in .env)
python scripts/audit_perf.py --plan    # speed audit: pages it would measure (run without --plan to measure)
python scripts/prioritize.py           # traffic + score per finding (needs .env; --offline reuses cache)
python scripts/findings.py summary     # findings store: summary | list | import-seed | import-discovery|import-audit <json>
python scripts/build_report.py <run json> --notes reports/discovery-notes.txt --audit-notes reports/crawl-audit-notes.txt --out reports/discovery-latest.html
```

Conventions:
- **Report changes apply to the latest report only (SK, 2026-10-12):** rebuild only `reports/discovery-latest.html` and the Pages report. Never regenerate or edit older report pages (`reports/discovery-*-runN.html`) or older run JSONs; a backfill may touch only the latest run file.
- Tests are offline: inject fake clients (see `FakeGSC`, `FakeGA4`); never hit the network or Google in `pytest`.
- Google and HTTP libraries are imported lazily inside functions so offline tests do not need them.
- Errors in reports are short and secret-free (`_err()` pattern). Never print or store key material or tokens.
- `core/` must not contain the string "aspose" (a test enforces this).
- New dependencies go in `pyproject.toml` under the right extra.
- **Per tenant (2026-10-20):** every path below is inside `reports/<tenant>/` or `data/<tenant>/` (`core/paths.py`); older entries in this file name the pre-2026-10-20 paths (`reports/x` is now `reports/aspose.app/x`).
- Generated files go to `reports/` (**committed**: the repo is private and internal, SK 2026-10-08) or `data/` (gitignored: `inventory.sqlite` is ~750 MB and rebuilt by `discover.py`; `findings.sqlite` is exported to `reports/findings.json`). Never put key material in reports. Discovery runs kept in `reports/`: full runs 3 (before the double-slash/guessed-URL fixes), 6 (first clean run) and 7 (first run in the findings store). Sample runs 1, 2, 4 were deleted; run 5 was stopped early and has no file. Commit only full runs; delete sample-run JSON before committing. Audits share `data/audit.sqlite` (gitignored; run ids count across auditors). Run JSONs kept in `reports/`: crawl audit run 15, speed audit run 12, AI audit run 16, text check run 23 (earlier crawl runs 5-9 and AI run 14 deleted as superseded).

## Multi-tenant rule

Nothing in `core/`, `mcp_servers/` or `agents/` may name aspose.app. Everything domain-specific goes in `tenants/<property>.yaml` (`property` must equal the file name): `tenants/aspose.app.yaml`, `tenants/aspose.cloud.yaml`, `tenants/groupdocs.cloud.yaml` and `tenants/conholdate.cloud.yaml` (blog.conholdate.cloud, GSC `https://blog.conholdate.cloud/`, GA4 `253119926`, 23 languages, URL templates home/listing/post/category). Keys, with aspose.app's values:

| Key | Meaning |
|---|---|
| `property` | Tenant name |
| `excluded_host_patterns` | Never crawl or check (`*-qa.*`) |
| `google_credentials_env` | `.env` variable with the tenant's service-account key path (default `GOOGLE_APPLICATION_CREDENTIALS`; conholdate.cloud: `GOOGLE_CREDENTIALS_HEALTH_AND_RECOVERY`) |
| `languages` | Optional language codes for URL classification (conholdate.cloud sets its 23) |
| `gsc_properties` | URL-prefix GSC properties: products, about, blog, releases, websites |
| `ga4_property_id` | `253117495` (confirmed) |
| `hosts` | 11: www, products, about, blog, forum, websites, releases, purchase, dashboard, metrics, status (api.products dropped 2026-10-20), with platform and known sitemap/robots/repo |
| `product_families` | The 29 `/<family>/` sections of products.aspose.app |
| `gsc_sitemaps_snapshot` | GSC → Sitemaps for products, as of 2026-10-08 (path, type, status, discovered) |

Hierarchy: **property → subdomain → template → page.** Group findings by template: one template fix corrects thousands of pages.

## Tenant 1: aspose.app

| Subdomain | Platform | Role | Fix channel (Phase 2) |
|---|---|---|---|
| www | Unknown | Main entry; 36 language homepages (`/fr/`, `/de/`, …) | Unknown |
| products | Hugo 0.110 | Core landing pages, 29 product families, hundreds of apps | Git PR (hubs only, see below) |
| blog | WordPress 5.7.2 multisite | Top of funnel | WP REST API / WP-CLI |
| forum | Discourse 3.1.1 | Long-tail questions; signal source for broken apps | Admin API, theme |
| about | Hugo 0.135 | Trust and legal; has `llms.txt`, `llms-full.txt`, `.md` endpoints | Git PR |
| websites | Hugo 0.110 | Links across the Aspose network | Git PR |
| releases | Static, platform unconfirmed | Micro-app downloads | Git PR, repo unconfirmed |

SK's list ended with "etc", so the Discovery agent must find every host from DNS, sitemaps and internal links. Do not rely on this table.

### products.aspose.app source repo

- Local: `/Users/Apple/Work/Aspose/GitHub/aspose-app/products.aspose.app` (GitHub `Aspose/products.aspose.app`, branch `main`). Read-only in Phase 1.
- Covers only the homepage and the 29 family hubs: 59 `_index.md` files (`/<family>/` and `/<family>/family/`). The individual app pages (`/pdf/conversion`, `/words/merger`, …) are not in this repo; their source is unknown.
- Theme: `themes/lutsk-aspose-theme` (layouts, shortcodes, `structured-data.html`, `robots.txt` template).
- Deploy: `hugo deploy` to Ceph S3 (staging `products-qa`, production); workflows run manually from `Aspose/products.aspose.app-workflows`.

## Audit dimensions

Each finding answers one of: broken, not optimized, incorrect, improvable.

1. `crawl` – status codes, redirect chains, robots.txt, sitemaps, canonicals, noindex, orphans
2. `perf` – Core Web Vitals (LCP, INP, CLS), rendering, mobile, HTTPS
3. `onpage` – titles, metas, headings, duplicate or thin pages, internal links, alt text
4. `schema` – structured data validity and coverage
5. `intl` – hreflang, translation parity, language and URL consistency
6. `content` – factual accuracy, stale info, intent match, cannibalization
7. `ai` – AI crawler access, answer-ready structure, entity clarity, llms.txt, citations in AI answers
8. `functional` – apps work end to end (upload, convert, download), broken links, JS errors, uptime
9. `ux` – engagement signals, accessibility (WCAG), layout
10. `authority` – backlinks gained and lost, toxic links, brand mentions
11. `competitive` – keywords and SERP or AI features competitors win
12. `cross` – issues between subdomains: stale cross-links, blog vs product cannibalization, mismatched language sets
13. `platform` – outdated CMS or generator versions (security and performance risk)

## Agents

- **Discovery/Inventory** – hosts, URLs, template map
- **Auditors** – one per dimension above
- **Diagnosis/Recovery** – correlates traffic drops with deploys, algorithm updates, index changes
- **Prioritizer** – scores findings by impact × effort, using GSC and GA4 data
- **Reporter** – scorecards per subdomain and for the whole property
- **Fixer, Verifier** – Phase 2 only

## Finding schema (confirmed)

```json
{
  "id": "crawl-0001",
  "tenant": "aspose.app",
  "subdomain": "forum.aspose.app",
  "template": "footer",
  "dimension": "cross",
  "type": "broken | not_optimized | incorrect | improvable",
  "title": "Footer legal links point to a retired host",
  "evidence": {"urls": [], "observed": "", "expected": ""},
  "affected_pages": 0,
  "impact": {"clicks_28d": 0, "impressions_28d": 0, "score": 0},
  "effort": "S | M | L",
  "fix_tier": 1,
  "fix_channel": "discourse-admin",
  "status": "open",
  "detected_at": "2026-10-07"
}
```

Every finding needs evidence a human can re-check. No finding without a URL and an observed value.

## Autonomy tiers (Phase 2, inactive)

1. **Auto-fix and merge:** broken links, missing alt text and meta descriptions, schema errors, typos.
2. **Auto-fix with canary:** titles, canonicals, internal linking, template changes. Small page set first, Verifier checks, then roll out or roll back.
3. **Human approval:** robots.txt, noindex, bulk redirects, URL changes, content removal, platform upgrades.

## Data sources and secrets

- Google Search Console and GA4 through a read-only service account: since 2026-10-20 `sk-serv-acc@health-and-recovery.iam.gserviceaccount.com` (project `health-and-recovery`, number 385867072171) for every tenant; SK added it to all aspose.app GSC properties and GA4 253117495, and to blog.conholdate.cloud GSC and GA4 253119926. Enabled in that project: Search Console API, Analytics Data API, PageSpeed Insights API (the Analytics Admin API is off, so GA4 properties cannot be listed).
- GSC: URL-prefix properties exist for products, about, blog, releases and websites (`https://<host>.aspose.app/`). www and forum are not listed yet. Query each property separately and merge per host.
- GA4 property ID: GA4 → Admin → Property details (a number, not the `G-` measurement ID). Subdomains may share one property or use several.
- Key paths come from `.env`: `GOOGLE_APPLICATION_CREDENTIALS` (default, also used by the `gsc` MCP server and PageSpeed) and `GOOGLE_CREDENTIALS_HEALTH_AND_RECOVERY` (named by conholdate.cloud's `google_credentials_env`); both point at the new key in `/Users/Apple/Work/Aspose/keys/service accounts/`. Key files stay outside this repo. Never commit, print or paste keys or tokens.
- Also planned: Bing Webmaster Tools, CrUX/PageSpeed, server logs, own crawl, optional rank and backlink API.
- Blog and forum are not Git-driven; they will need API credentials (read-only in Phase 1).

## Discovery results (full run 3, 2026-10-08; verified live)

534 sitemaps, 584 requests, ~15 min at 1 req/s/host. **769,659 unique URLs** in sitemaps: products 722,942, forum 41,891, metrics 3,780, releases 308, about 234, websites 215 (incl. cross-folder), status 150, blog 153, www 36. purchase, dashboard, api.products: no sitemap. No unknown aspose.app hosts referenced in sitemaps.

- **robots.txt:** missing (404) on products, about, websites, dashboard, api.products. purchase returns an HTML page for robots.txt. Present but no `Sitemap:` line on www, blog, metrics, status. Only forum and releases list their sitemap.
- **products sitemaps vs GSC:** most families match GSC exactly. Differences explained:
  - **slides:** `/slides/sitemaps/slides.xml` lists its 16 children as `https://products.aspose.app//slides/...` (double slash) → HTTP 503; the single-slash URLs work (24,752 URLs). GSC still says Success/24,804, likely from an older read. Verified with curl.
  - **imaging:** 229,372 in GSC vs 149,240 unique live; the imaging sitemaps list **80,132 duplicate entries** inside files (GSC counts duplicates).
  - Broken live: root `/sitemap.xml` 404, `/omr/sitemap.xml` and `/omr/sitemap-percentage.xml` 404 (omr: no working sitemap at all), `/drawing/sitemap.xml` 503 (drawing: none), `/gis/sitemaps/sitemap.xml` 404 (gis still covered by `/gis/static/sitemap/*`), `/video-app/sitemap.xml` 200 but empty.
  - Small gaps: 3d 44,590 → 43,680 live, psd 13,300 → 12,768, gis 18,178 → 17,739 (sitemaps shrank since GSC read).
- **hreflang in sitemaps:** full on words, cad, ebook (products), about, metrics, www. Partial: email 22%, finance 2%, websites ~50%. **None on the other 21 products families**, incl. cells (228k), imaging (149k), audio, diagram, video, 3d, pdf. Page HTML still to check in the intl audit.
- **lastmod:** every URL in a file shares one date (bulk-stamped) in 22 products families; none at all on about, metrics, releases, status, websites, www, total, slides.
- **Duplicates across sitemaps:** small (diagram 267 via `sitemap_update.xml`, websites folders, www 35, forum 22).
- metrics.aspose.app exposes 3,780 usage/subscription pages in 36 languages via sitemap; status.aspose.app lists 150 incident/date-query URLs (`?start_date=`). SK (2026-10-09): both are meant to be indexed, like blog.
- **Soft 404 (products):** `/email/sitemap.xml` redirects to `/email/error?code=404`, which returns HTTP 200. Check app error pages for soft 404s in the crawl audit.
- **Run 6 (after fixes):** slides child sitemaps fetched via corrected URLs (24,752 URLs); products 747,694 URLs, total ~794k; 89 findings. **Correction (crawl audit, 2026-10-09):** every one of those 24,752 slides page URLs is itself listed as `https://products.aspose.app//slides/...` and returns 503, so slides has no usable sitemap at all; GSC only knows the single-slash URLs (567 pages, 12k clicks), found via links. Report page built by `scripts/build_report.py` (template `scripts/templates/discovery_report.html`), takeaways in `reports/discovery-notes.txt`.
- Discovery fixes after run 3: double-slash child check (fetches the corrected URL too); parse/redirect/empty checks only on real sitemaps (robots, GSC, child), not on guessed URLs; duplicate findings grouped per host unless the host has sections.

## Seed findings (manual review, 2026-10-07..08)

Issues found by hand in the claude.ai session (live pages, sitemaps, products repo) that discovery code does not produce. **Source of truth: `tenants/aspose.app.seed-findings.yaml`** (confirmed finding schema + a `verification` block). `tests/test_seed_findings.py` validates it. 29 findings, 14 verified (4 superseded by crawl-audit findings, 2026-10-08), plus `notes` (cause/context attached to a discovery finding by its key).

Rules:
- `status: open` = verified in repo and/or live; `status: unverified` = seen once by a web fetcher. Re-check before any report.
- Each entry's `verification.recheck` names the auditor check that must detect it automatically. Build those checks; when an auditor reproduces a seed finding, keep the auditor's finding and mark the seed `superseded_by: <id>`.
- The findings store imports this file on every `discover.py` run (or `scripts/findings.py import-seed`). The file stays the source of truth for seed status; a seed removed from the file is marked resolved.
- A cause or context for a discovery finding goes under `notes:` with `applies_to: <dimension>/<check>/<subdomain>/<template>`, not as a new finding.
- Not repeated here (already found by discovery): robots.txt 404s, broken family sitemaps, sitemap hreflang/lastmod, slides double slash, imaging duplicate entries, email soft 404.

Highlights:
- **Verified copy errors on products hubs:** `/pdf/` title+H1 "edit **test** PDF"; `/svg/` and `/svg/family/` titles and descriptions describe **Photoshop PSD** (copied from psd); finance title "Free App **for for** finance - **Hanlde**"; omr "**Recoginze**".
- Hub titles sell "Solutions"/"On Premise APIs" on a free-apps site; each family has two near-duplicate hubs (`/<family>/` and `/<family>/family/`).
- App pages: locale versions without hreflang (sample `/pdf/conversion`).
- Other hosts: forum Diagram category says "Microsoft Project"; forum legal links go to `company.aspose.app`; websites alt text "aspose.org" for aspose.net; `user-scalable=no` on websites/releases/blog; about cites "1.17M visits in January 2021"; outdated WordPress 5.7.2 and Discourse 3.1.1.

| ID | Host | Finding | Verified |
|---|---|---|---|
| `seed-onpage-01` | products | PDF hub title and H1 contain the stray word 'test' | yes |
| `seed-onpage-02` | products | SVG hub pages carry Photoshop (PSD) titles and meta descriptions copied from the psd hub | yes |
| `seed-onpage-03` | products | Finance hub title has typos; family page title describes APIs, not free apps | yes |
| `seed-onpage-04` | products | OMR family page title misspells 'Recognize' | yes |
| `seed-content-01` | products | Hub titles and H2s talk about 'Solutions' and 'On Premise APIs' on a free-apps site | yes |
| `seed-content-02` | products | Each family has two near-duplicate hub pages: /<family>/ and /<family>/family/ | no |
| `seed-intl-01` | products | App pages have locale versions but no hreflang tags (not reproduced for pdf/barcode/html) | no |
| `seed-intl-02` | products | Hub pages emit no hreflang; theme logic exists but is limited to /svg/, /html/, /total/ (→ intl-0034) | yes |
| `seed-intl-03` | products | Language coverage differs widely between families | yes |
| `seed-crawl-02` | products | PDF sitemap index lists llms.xml, a sitemap whose only URL is /pdf/llms.txt | yes |
| `seed-crawl-03` | products | PDF splitter URL differs between sitemap and hub links | no |
| `seed-content-03` | products | Near-duplicate imaging conversion pages for the same JPEG 2000 target | no |
| `seed-intl-04` | www | www English sitemap is built differently from the other 35 language sitemaps | yes |
| `seed-platform-01` | products | products config still carries a retired Universal Analytics ID | yes |
| `seed-platform-02` | products | Hugo versions differ across hosts (products/websites 0.110, about 0.135) | no |
| `seed-platform-03` | blog | Blog runs WordPress 5.7.2 (2021), long out of support | no |
| `seed-platform-04` | forum | Forum runs Discourse 3.1.1 | no |
| `seed-content-04` | blog | Blog is barely updated and shows empty categories | no |
| `seed-cross-01` | forum | Forum footer legal links point to company.aspose.app | no |
| `seed-content-05` | forum | Forum Diagram category description says Microsoft Project instead of Visio | no |
| `seed-onpage-05` | websites | aspose.net entry uses 'aspose.org' as image alt text | no |
| `seed-intl-05` | websites | websites sitemaps cover 38 languages very unevenly; about covers 13 evenly | yes |
| `seed-cross-02` | websites | Home links for aspose.com and aspose.ai point to metrics.* hosts | no |
| `seed-ux-01` | websites | Viewport disables zoom (user-scalable=no) on websites, releases and blog (→ ux-0005) | yes |
| `seed-onpage-06` | releases | Releases homepage has no canonical and no meta description (→ crawl-0068) | yes |
| `seed-onpage-07` | about | about and websites homepages show no meta description (→ onpage-0012) | yes |
| `seed-content-06` | about | About page cites a 2021 traffic figure and a one-entry timeline | no |
| `seed-cross-03` | about | About links to websites.aspose.com instead of websites.aspose.app | no |
| `seed-ai-01` | products | Only about (and /pdf/) offer llms.txt; other hosts have none | no |

## Background notes (earlier claude.ai session)

Context gathered before discovery existed. The issues in it are tracked in `tenants/aspose.app.seed-findings.yaml` or in discovery findings; keep this section for background only.

- products, **verified live and in repo:** `/pdf/` title and H1 read "Free Online Apps to view, convert, edit **test** PDF" (`content/pdf/_index.md`).
- products: `/robots.txt` and `/sitemap.xml` returned 404 to a web fetcher; confirm with curl from the Mac. robots.txt and sitemaps are per host, so www's files do not cover products.
- products repo: the Hugo build does generate both files (`enableRobotsTXT = true`, Hugo's default sitemap is not disabled), and live canonicals are absolute, so CI overrides `baseURL = "/"`. Likely cause of the 404: products.aspose.app is path-routed (Hugo hubs in S3 + a separate app platform), and `/robots.txt` and `/sitemap.xml` are not routed to the Hugo bucket. Confirm with whoever owns the routing / CDN.
- products repo: robots template emits only `User-agent: *` (no `Sitemap:` line); unchanged since first commit (2024-02-26).
- products app pages (e.g. `/pdf/conversion`): separate platform (`/pdf/apps-ui/` assets), absolute canonical, locale variants at `/<family>/<lang>/<app>`, but **no hreflang tags seen** in page HTML. Verify on raw HTML.
- products app sitemaps exist **per family** at `/<family>/sitemap.xml` (sitemap indexes), each in a different format, which suggests a separate codebase per family:

  | Family | Child sitemaps | Languages | lastmod | hreflang |
  |---|---|---|---|---|
  | imaging | `/imaging/sitemap.<lang>.xml` | 52 | none on index; every URL in `en` = 2026-04-17 (bulk-stamped) | none |
  | cells | `/cells/sitemap-<lang>.xml` | 37 | all 2026-09-21 | none |
  | pdf | `/pdf/sitemaps/pdf.<lang>.xml` + `llms.xml` | 29 | per URL, 2026-08-26..09-30 | none |
  | words | `/words/common/<tool>.xml.gz` (split by tool, not language; gzipped, download + decompress) | 40 (per SK) | present | none |

  `imaging/sitemap.en.xml` has 500+ URLs, `pdf/sitemaps/pdf.en.xml` ~573 (fetcher truncated both; counts are minimums). Patterns: `/<family>/<tool>`, `/<family>/conversion/<fmt>`, `/<family>/conversion/<src>-to-<dst>`.
  Discovery must probe `/<family>/sitemap.xml` for all 29 families. With no root `/sitemap.xml` and no robots.txt, search engines find these only if submitted in GSC.
- products, **from GSC → Sitemaps (SK, 2026-10-08):** 38 sitemaps submitted, all 29 families covered, ~880k discovered URLs in total. Full list in `tenants/aspose.app.yaml`.
  - imaging (229k) and cells (228k) are 52% of all discovered URLs. Compare with indexed counts: likely index bloat or thin programmatic pages.
  - **No working sitemap:** omr (both sitemaps "Couldn't fetch" since mid-2025, 50k URLs previously discovered) and drawing ("Couldn't fetch").
  - Also failing: `/gis/sitemaps/sitemap.xml` (since Apr 2025; the `/gis/static/sitemap/*` ones work), root `/sitemap.xml` (matches the 404), `/video-app/sitemap.xml` (1 error, 0 URLs).
  - Legacy or overlapping entries: diagram `sitemap_update.xml`, psd `sitemap.en.xml` beside its index, finance `sitemap_all.xml`, three gis sitemaps.
  - At least 6 path conventions (`/sitemap.xml`, `/sitemaps/<x>.xml`, `/sitemap/sitemap.xml`, `/static/sitemap/…`, `/sitemap` without extension), more evidence of one codebase per family.
  - GSC API can list sitemaps but not the Page indexing report; indexed-vs-discovered per family needs the UI export or URL Inspection sampling (2,000/day per property).
- products: language sets differ per family (imaging 52, words 40, cells 37, pdf 29), so translation parity is uneven.
- products/pdf: `pdf/sitemaps/llms.xml` is a sitemap whose only URL is `/pdf/llms.txt`. Sitemap lists `/pdf/split` while the homepage links `/pdf/splitter`; check for redirects or duplicates.
- products/imaging: near-duplicate conversion targets (`jpg-to-jp2`, `jpg-to-j2k`, `jpg-to-jpeg2000`); check for cannibalization / thin pages. The theme's `alt-links.html` already has hreflang logic for exactly this URL pattern (`langdirlevel`, `locales` params), but only `/svg/`, `/html/`, `/total/` pages use it; hub pages have no hreflang.
- www: `sitemap.xml` is an index of 36 language sitemaps, no `lastmod` anywhere. `/fr/sitemap.xml` (and presumably the others) holds 1 URL with 36 hreflang alternates; `/en/sitemap.xml` is inconsistent: it lists all 36 homepages, with alternates only on the root. Whole index covers only the 36 www homepages.
- www: `robots.txt` has only `Allow: /$` and `Allow: /sitemap.xml` (allows everything) and no `Sitemap:` line.
- products repo: `config.toml` still carries a Universal Analytics ID (`UA-…`, retired 2023); GA tracking itself comes via GTM.

- blog: WordPress 5.7.2; few recent posts; categories with 0 articles.
- forum: footer ToS and Privacy links point to `company.aspose.app`; Diagram category description says "Microsoft Project".
- websites: aspose.net logo alt text says "aspose.org"; 6 languages vs 13 on about.
- releases: no canonical or meta description seen on the homepage.
- about: already AI-readable (`llms.txt`); check whether other subdomains match.

## Next steps (in order)

1. ~~Run `check_access.py`~~ Done 2026-10-08 (see Status). All 5 URL-prefix properties are readable. Remaining gap: www and forum (and any other hosts Discovery finds) have no GSC property; a Domain property would cover them all. Not blocking step 2.
2. **Discovery (inventory)**: done. Latest run: **run 8** (2026-10-09; run 7 was the first in the findings store). Shared report: https://claude.ai/artifact/MUUTzbXEymKq4tw5mmmPA5 (private; SK shares via its Share menu). To refresh: `discover.py` / `audit_crawl.py` → `build_report.py <discovery run json> --notes reports/discovery-notes.txt --audit-notes reports/crawl-audit-notes.txt --out reports/discovery-latest.html` (picks the newest crawl-audit JSON; page now titled "aspose.app site health" with a Crawl audit section) → republish that file. For Pages: commit the new run files and `git push github master`; the workflow rebuilds and publishes. Original spec:
   - Fetch robots.txt and root sitemap per host; probe `/<family>/sitemap.xml` for all 29 families plus every path in `gsc_sitemaps_snapshot`.
   - Recurse sitemap indexes; handle `.xml.gz` (words) and BOMs; record per sitemap: URL, status, type, child count, URL count, lastmod spread, hreflang presence.
   - Normalise URLs to an inventory: host, family, language (from path), tool/template pattern (`/<family>/<tool>`, `/<family>/conversion/<fmt>`, `/<family>/conversion/<src>-to-<dst>`, `/<family>/<lang>/<tool>`).
   - Store in SQLite (`data/inventory.sqlite`, gitignored). Polite: identifiable user agent, rate limit, retries, respect robots.txt, skip excluded hosts.
   - Output: per-family / per-language URL counts vs the GSC snapshot; sitemap problems as findings.
3. ~~Findings store~~ Done 2026-10-08 (see Status). Report rebuilt locally from the store after run 7 (`reports/discovery-latest.html`); **republish to the shared link only when SK says so**.
4. ~~`mcp_servers/gsc`~~ Done 2026-10-08. `python -m mcp_servers.gsc` (MCPServer, stdio). Tools, all annotated read-only: `list_properties`, `search_performance` (dimensions page/query/country/device/date/searchAppearance, ANDed filters, totals, max 1,000 rows per call), `page_performance` (picks the property from the URL), `compare_periods` (last N days vs the N before: totals, top drops/gains), `list_sitemaps`, `inspect_url` (2,000/day/property, sampling only). Logic lives in `core/gsc.py`; the server only validates input and turns errors into short `ToolError`s. Loads the key path from `.env` if `GOOGLE_APPLICATION_CREDENTIALS` is unset. Registered in `.mcp.json` in the workspace folder (absolute paths, outside git) and in the repo (relative paths); **SK must approve it once** when Claude Code next starts (`claude mcp list` shows "Pending approval"). 9 offline tests (36 total). Verified end to end over stdio with the real key.
   - First answers (window 2026-09-08..10-05 vs the 28 days before): **slides** pages 12,044 clicks vs 10,125 (+19%), impressions 176k vs 189k (-7%): the broken slides sitemap has not hurt traffic yet (pages already indexed). **`/pdf/split`** 17 clicks / 635 impressions, **`/pdf/splitter`** 0 impressions. **`/imaging/conversion/jpg-to-jp2`** is indexed with its own canonical (URL Inspection).
5. ~~**Crawl auditor**~~ Built 2026-10-08; all 29 families audited 2026-10-09 (latest full run 9). `crawl` MCP server over `core/audit` is in priority 4.
6. **LangGraph** run graph once 2+ auditors exist; Reporter after that.

**Priority order agreed with SK (2026-10-09):**
1. ~~**Prioritizer**~~ Done 2026-10-09 (see Status).
2. ~~**Crawl audit of the other 27 products families**~~ Done 2026-10-09 (runs 6-8, see Status).
3. **New auditors**: perf (PageSpeed/CrUX; built and run 2026-10-15), ai (llms.txt, AI bot access; built and run 2026-10-16), text check (LLM, built and run 2026-10-20). Functional (apps upload/convert/download) **postponed** (SK, 2026-10-20: furthest from the traffic goal, most expensive; the Aspose.ai monitor already does browser smoke tests).
4. **MCP servers**: `findings`, `crawl` (then `ga4`, `pagespeed`). Next after the text check.

**Ideas from the Aspose.ai Website Health monitor** (https://aspose.github.io/aspose-ai-website-health/, reviewed 2026-10-09). It is an ops/uptime monitor (7 hosts, availability, priority links, Playwright smoke + screenshots, daily/weekly digests, static `dashboard.json` + `app.js` on Pages), complementary to this SEO/GEO audit. Worth adopting:
- Overall score + per-dimension bars, and scorecards per subdomain (the Reporter). Keep them evidence-backed: theirs shows 100/healthy from shallow checks.
- A short "needs review" list at the top, ranked by the Prioritizer.
- Priority pages checked every run: top GSC pages and the purchase/conversion paths.
- An `owner` per host/section in the tenant YAML, shown on each finding.
- Browser checks with screenshots as evidence, for the functional and ux auditors.
- Scheduled discovery + crawl audit in GitHub Actions (no Google key needed), with a new/resolved digest per run from the findings store.
- Data in a separate JSON beside the page, for run history and trends.
- aspose.ai could be tenant 2 later (core/ is tenant-agnostic).

## Open items

- **Old service account (2026-10-20):** `sk-service-acc@aspose-app-health-and-recovery` and its key file (`aspose-app-health-and-recovery.json` in `keys/service accounts/`) are no longer used anywhere. SK may delete both after restarting Claude Code (the `gsc` MCP server running then still held the old key). Remind SK until done.
- **Private domain (SK, 2026-10-20: soon):** both reports move off public GitHub Pages; until then they are public (noindex).
- **LLM key (2026-10-20):** `.env` has `PROFESSIONALIZE_API_KEY` / `_BASE_URL` / `_LLM_MODEL` (internal OpenAI-compatible LLM, same `openai` client pattern as `conholdate/blog-translation-agent`). For now it is the **translation agent's key**; SK is requesting a dedicated one, and production will use a different key. Remind SK until the new key is in place. Sending public aspose.app page text to it is fine (SK).

- Source of the individual app pages on products, and repos for about, websites, releases, not shared yet. This repo holds the agents, not the sites.
- GA4 property `253117495` is readable and covers all subdomains (verified 2026-10-08). GSC: service account reads all 5 URL-prefix properties (products, about, blog, releases, websites). GSC properties for www and forum still missing. SK (2026-10-08): **all subdomains are in scope**, so GSC must cover every host. Recommended: a Domain property `sc-domain:aspose.app` (DNS-verified, covers all subdomains) with the service account added as Restricted user. Auth stays service account, not SK's personal OAuth (see conversation 2026-10-08).
- GA4: 241k sessions with an empty hostName (205k organic) and spam/foreign hosts. Ask who owns the GA4 setup whether a hostname filter exists.
- Page indexing (indexed vs discovered) per family: needs SK's export from GSC → Indexing → Pages, or URL Inspection sampling.
- SK checking: who owns routing/CDN for products.aspose.app, and where the app pages are built. Not blocking Phase 1: audit runs on the live site; repos are needed for root cause and Phase 2, requested only for the highest-impact families.
- Host list: Discovery covers 11 hosts (7 from SK + 4 seen in GA4; api.products dropped 2026-10-20); sitemaps reference no other aspose.app hosts. Not yet done: DNS / certificate-transparency enumeration to find hosts nothing links to.
- forum.aspose.app sitemap lists private topics (403 for everyone, 20/20 sampled). Ask the forum owner whether private categories should be excluded from the Discourse sitemap.
- ~~metrics/status indexing~~ SK (2026-10-09): metrics.aspose.app and status.aspose.app are normal indexable hosts like blog; count their findings in full.

## Repo-specific additions

# AGENTS.md — working in cms-platform

Reusable CMS machinery extracted from **adamdaniel.ai**, so new sites get the
same Jekyll + Decap + AWS stack and platform improvements sync **both ways**.
Read this before changing anything here. Design: `docs/ARCHITECTURE.md`. Sync
model: `docs/SYNC.md`.

**Current release: `v0.1.72`** — `v0.1.0`–`v0.1.72` are all tagged GitHub
releases; cut a new one with `gh workflow run release.yml -f version=vX.Y.Z`.
Consumers: **adamdaniel.ai** (consumer #1, dogfood; gem-delivered admin live on
prod) and **jodidaniel.com** (consumer #2; single-page bio, gem admin + 9
per-section collections, `base_collections: []`, gated coming-soon). See
"Admin delivery (gem-shipped, v0.1.4+)", "Version history", and "Roadmap /
open issues" below.

## The model

Two repos. **This repo owns all machinery** (versioned, semver tags). A **site
repo** holds only content + identity (`_config.yml`) + thin consumers. Site
content/branding/docs **never** sync; platform/infra/CI/tooling/skills do;
structural scaffolding (collection types) is opt-in via the SITE-owned seam
`admin/collections.site.yml`. The Decap admin UI itself ships **inside the
theme gem** (since v0.1.4) — consumers no longer vendor a byte-copy of `admin/`;
they keep only the seam. See "Admin delivery" below.

## Layout

| Path | Layer |
|---|---|
| `.github/workflows/*.yml` | reusable `workflow_call` workflows (deploy, skills-sync, drift-guard, platform-bump) |
| `scripts/` | platform-owned helper scripts (preview slug, preview-config patch, Decap render, `audit-editorial-labels.js`, `write-commit-json.sh`) |
| `infrastructure/`, `oauth-proxy/` | parameterized CloudFormation + deploy scripts |
| `theme/` | the `cms-platform-theme` Jekyll **gem** (gemspec at `theme/`, so the gem root is `theme/`): layouts/includes/assets/plugins + the Decap render hook (`lib/cms-platform-theme/decap_config_hook.rb`) + the `admin/` UI |
| `theme/admin/` | Decap base config (`*.base.yml`) + admin JS/HTML/CSS (read `window.CMS_*`) + `reviews/` dashboards. Ships INSIDE the gem (since v0.1.4 — it had to move under `theme/` to be packaged); the render hook copies it into `_site/admin` and renders `config.yml`. Sites own only the seam `admin/collections.site.yml` (the gem ships no `collections.site.yml`). |
| `theme/spec/` | plain-ruby theme unit tests (`ruby theme/spec/<name>_test.rb`; no rspec/minitest dep beyond the stdlib `minitest/autorun` used by some); excluded from the gemspec `spec.files` glob |
| `skills/` | canonical Claude Code skills |
| `examples/site/` | copyable thin-shell callers a site consumes |
| `scaffold/` | `create-site.js` — the `npx` site generator |

## Conventions (do not break)

- **Port from `adamdaniel.ai@main`** — that's the source of truth. Don't invent;
  lift and parameterize.
- **Never hardcode `adamdaniel` identity.** Site values come from `_config.yml`
  (`cms.*`, `url`), workflow inputs, CFN params (`ResourcePrefix`,
  `ProductionDomainName`), `github.repository`, or injected `window.CMS_*`.
- **The /admin logo is SITE-OWNED; the gem ships only a NEUTRAL placeholder**
  (issue #25). `theme/assets/images/logo.svg` is a wordless, brand-free generic
  glyph — NEVER a specific site's mark (no "AD"/initials/wordmark). The render
  hooks default `cms.logo_url` to `<url>/assets/images/logo.svg`, and a site
  brands `/admin` by **shadowing** that gem asset with its own
  `assets/images/logo.svg` (Jekyll site files win over same-path gem files) or by
  setting `cms.logo_url`. The scaffolder seeds a "replace me" copy into every new
  site. Locked by `theme/spec/neutral_logo_test.rb` (gem asset is wordless +
  carries the override comment) and `e2e/scaffold-seeds-neutral-logo.test.js`
  (scaffold output). Don't reintroduce a brand into the gem asset.
- **The scaffolder seeds `preview.md` + `404.html` (issue #23).** A consuming
  site MUST expose `/preview/` (the admin "Live Preview" target) and a graceful
  `404.html`, or the admin button dead-ends on a raw S3 404 and unknown URLs 404
  ungracefully. The gem ships `theme/_layouts/preview.html` (the preview SHELL,
  with the hidden post/page/project variants the admin `preview-bridge` streams
  into) + the admin scripts, but the consuming site must provide the `/preview/`
  PAGE. `scaffold/create-site.js` seeds both (`SEED_PREVIEW` / `SEED_404`):
  `preview.md` is **front-matter only** (`layout: preview`, `permalink: /preview/`,
  `sitemap: false`) and carries **no front-matter `robots`** — the gem preview
  layout HARDCODES `<meta name="robots" content="noindex, nofollow">`, so a
  front-matter one would duplicate it (mirrors `adamdaniel.ai/preview.md`).
  `404.html` rides the gem `default` layout (which DOES render `page.robots`), so
  it carries `robots: "noindex,nofollow"` + `sitemap: false` + a home/blog link;
  copy is generic (no site identity). The `e2e/fixture-site` carries both (it
  represents a scaffolded site) and the platform lint
  `e2e/scaffold-preview-and-404.test.js` asserts the contract: (a) scaffold
  output, (b) fixture parity, (c) optional post-build proof that
  `_site/preview/index.html` renders the `data-preview-root` shell +
  `_site/404.html` exists (skips when no Jekyll toolchain — pure-fs self-CI
  lanes). **Single-page-site caveat:** per-item *live* preview is limited for a
  single-page bio (jodidaniel.com — no per-section route to drive the bridge);
  the seeded `preview.md` still gives a working `/preview/` shell + the seeded
  `404.html` a friendly not-found page.
- **Branch + PR, never push to `main`** (the auto-mode classifier enforces this).
- **Repo settings/rulesets change ONLY via a `repo-settings.yml` PR followed by
  a human `node scripts/audit-repo-settings.js --fix --yes`.** Emergency live
  flips must be ratified (PR the value in with a `# why:`) or reverted the same
  day — the daily `repo-settings-audit` workflow files a `ci` tracking issue on
  any drift.
- **SHA-pin every workflow `uses:`** with a `# vX.Y.Z (date)` comment; 7-day
  cooling-off before bumping (mirrors adamdaniel.ai policy).
- **Verify before claiming done** — run the render, drift-guard, scaffolder
  against throwaway inputs; syntax-check YAML/bash/Ruby/JS. See "Verify" below.
- **Record knowledge here (AGENTS.md) and/or in `skills/`, not only in agent
  memory** — Adam's standing preference.
- **Two render paths stay in lockstep.** The live Decap config + `window.CMS_*`
  identity globals are produced by BOTH `scripts/render-decap-config.rb`
  (deploy-time) and the theme-gem Jekyll hook
  `theme/lib/cms-platform-theme/decap_config_hook.rb` (build-time — the path gem
  consumers use). Both must inject the same keys
  (`CMS_REPO`/`CMS_SITE_ORIGIN`/`CMS_APEX`/`CMS_OAUTH_BASE_URL`/`CMS_SITE_TITLE`)
  into the same shells (`admin/index*.html` + `admin/reviews/*.html`);
  `e2e/decap-config-render-parity.test.js` fails on drift. Admin chrome (titles,
  reviews dashboards) reads identity from these globals — never hardcode it.
- **`GITHUB_SCOPE` is lockstepped across three files** — `oauth-proxy/lambda.py`,
  `oauth-proxy/template.yaml`, `oauth-proxy/deploy.sh` (default `repo,user,workflow`).
- **De-identified prose uses placeholders:** `<apex>` (production apex), `*.<apex>`,
  `<prefix>` (apex with dots→hyphens), `<owner>/<repo>`, `<your-site>`.
- **Theme-gem ruby unit tests live in `theme/spec/`** (plain ruby — no rspec/minitest;
  `ruby theme/spec/<name>_test.rb`); excluded from the gemspec `spec.files` glob.
- **`e2e/` deps install via `cd e2e && npm ci`** (`e2e/package-lock.json` is tracked —
  consumers need it). The CloudFront-Function specs simulate `Fn::Sub` by substituting
  a synthetic `example.test` apex, so platform specs stay site-agnostic.
- **AST always, never regex, for code-shape lints (Adam's standing rule).** A lint
  that reasons about CODE STRUCTURE — which `test()` blocks exist, whether a
  `guard(SITE_ROOT, …)` sits inside a given test's scope, which collection a
  `page.goto` navigates — MUST parse a real AST, never regex-scan the source.
  Regex on source is brittle: it false-matches tokens in comments/strings,
  mis-reads across line breaks, and is BLIND to interpolation — a regex couldn't
  see `page.goto(\`…#/collections/${CANARY.cmsCollection}\`)` (a *variable*
  collection), which let the jodidaniel host-loop guard gap ship. Parse with
  `e2e/spec-ast.js` (acorn + acorn-walk): `analyzeSpec(src)` returns a fact bag
  (string VALUES with `${…}` placeholders, call names+args, identifiers, requires,
  Program-level `test()` blocks); the detector matches those facts, not raw text.
  This mirrors `e2e/workflow-yaml-utils.js`, which parses workflow YAML with the
  `yaml` parser for the same reason. The guard-registry detector
  (`base-collections-guard-registry.test.js`) + `platformMetaSpecs()` are AST-based;
  any NEW code-shape lint must be too. (Regex stays fine for genuinely lexical
  concerns — a version string, a leaf token's content — never for code structure.)
  Adding the parser deps respected the 7-day dependency cooling-off (above).

## Admin delivery (gem-shipped, v0.1.4+) — the render hook, the seam, base_collections

The Decap admin (`/admin`) is the ~400-line invariant-heavy CMS config plus a
set of JS/HTML/CSS shells and the `reviews/` dashboards. Two facts drive the
whole design:

1. **The gem root is `theme/`** (the gemspec lives there). For the gem to ship
   the admin machinery, `admin/` had to live **under** the gem root, so it was
   relocated from the repo root to `theme/admin/` in **v0.1.4**. (RubyGems drops
   `..` paths and won't follow symlinks, so a sibling `admin/` couldn't be
   packaged.) The gemspec packages `admin/**/*` **minus** the site-owned seam and
   the build-generated files (`collections.site.yml`, `config.yml`,
   `config-local.yml`, `commit.json`) — via `Dir[] - Dir[]` array subtraction,
   because `Dir[]` has no `!` negation.

2. **Consumers stop vendoring `admin/`.** A consuming site deletes its vendored
   `admin/` and keeps **only** the seam `admin/collections.site.yml` (+
   `.example`). The down-sync path is a gem bump (Dependabot `bundler`).
   `platform-drift-guard` is now **skills-only** (admin is no longer
   byte-guarded).

**The render hook** (`theme/lib/cms-platform-theme/decap_config_hook.rb`, a
`:site, :post_write` Jekyll hook) does, at the end of every build:

- **Resolve machinery inputs from the gem** (`site.theme.root/admin`), falling
  back to a vendored `site.source/admin` (migration window + the platform's own
  e2e fixture). No-op if neither has a `config.base.yml`.
- **Copy the gem-resident machinery into `_site/admin`** — Jekyll won't, since
  the site tree no longer contains `admin/`. It copies depth-1 files + the
  `reviews/` subdir only (skipping `*.base.yml`, the seam, `README.md`). **If you
  add another subdirectory under `theme/admin/`, extend this copy AND its parity
  sibling `scripts/render-decap-config.rb`.**
- **Render `config.yml` from `config.base.yml`** by token-substituting the
  `window.CMS_*` identity (`{{CMS_REPO}}`, `{{CMS_OAUTH_BASE_URL}}`,
  `{{CMS_SITE_URL}}`, `{{CMS_DISPLAY_URL}}`, `{{CMS_LOGO_URL}}`) and **splicing
  the SITE-OWNED seam** `admin/collections.site.yml` at the `# __SITE_COLLECTIONS__`
  marker. The seam is read from the **SITE source**, never the gem. Before the
  splice, the seam's `$ref`s are expanded against the platform `field_library`
  (see "field_library + `$ref` reuse" below) — the base config itself stays
  TEXT and is spliced byte-for-byte as today.
- **Inject `window.CMS_*` globals** into the admin shells (`index*.html`) AND the
  reviews dashboards (`reviews/*.html`) — skipping a file only if it already
  *defines* the identity, not merely uses it.
- **Delete `*.base.yml`** from the output (the templates aren't published).

`scripts/render-decap-config.rb` is the **deploy-time CLI mirror** of the hook
(same copy + render + inject + cleanup; resolves the gem via
`Gem.loaded_specs['cms-platform-theme']`). The two are **parity-locked** by
`e2e/decap-config-render-parity.test.js` — keep the injected globals and the
`index*` / `reviews/*` globs **identical** in both, or the lint fails.

**`write-commit-json.sh`** writes `_site/admin/commit.json` (the commit pill's
`fetch('commit.json')` resolves under `_site/admin/` now that admin is served
from there; CI deploys do this automatically — the script is for local dev).

### base_collections opt-out (v0.1.7)

`_config.yml` `cms.base_collections` is a **KEEP-LIST** of the platform's
built-in collections (`posts tags projects pages e2e`):

- **UNSET** → keep all (default, back-compat).
- `[]` → hide them all, so `/admin` shows ONLY the site's own collections.
- a subset → keep only those.

The renderers delete each unwanted top-level collection block by regex —
matched at **2-space indent**, through to the next top-level `- name:` or EOF;
nested fields are deeper-indented so they survive. **Spec-locked** by
`theme/spec/base_collections_filter_test.rb` (asserts nil keeps all, `[]` hides
all base collections but keeps site collections, partial keep works, survivors'
nested fields and a field literally named like a base collection are untouched,
output stays valid YAML). Used by single-page sites (jodidaniel.com).

### field_library + `$ref` reuse (#5 GOAL 2)

A site's seam `admin/collections.site.yml` can **reuse** platform-defined
field/widget defs instead of re-authoring them, by writing a `$ref` where a
field (or fields) would go:

```yaml
  - name: articles
    folder: _articles
    fields:
      - { name: title, label: Title, widget: string }   # inline still works
      - $ref: "#/field_library/body_markdown"            # → ONE field
      - $ref: "#/field_library/image_widget"             # → ONE field
      - $ref: "#/field_library/published_pair"           # → TWO fields (spliced)
```

- **The platform OWNS the library:** `theme/admin/field_library.yml` (ships in
  the gem next to `config.base.yml`, packaged by the `admin/**/*` glob). It
  defines `body_markdown` (markdown body, modes rich_text+raw), `published_pair`
  (the published + publish_date pair — a **list** of 2 fields), `date_widget`,
  `image_widget` (flat-public_folder contract). The datetime `format:` token
  (`"YYYY-MM-DD HH:mm:ss ZZ"`) is copied **verbatim** from `config.base.yml`
  (the dayjs/INVALID-DATE cross-engine contract) — keep them in lockstep.
- **Resolved at RENDER time, in BOTH paths.** The shared resolver
  `theme/lib/cms-platform-theme/field_library.rb`
  (`CmsPlatformTheme::FieldLibrary`) is `require`d by **both** render paths and
  invoked identically — `expand_seam_text(raw, field_library_path)` — so they
  stay byte-in-lockstep. It parses the seam, replaces each
  `{"$ref" => "#/field_library/<name>"}` with a **deep copy** of the lib entry
  (single field → one item; list → spliced in place, 2-space list indent
  preserved), then re-emits YAML and splices at the marker. **Decap never sees a
  `$ref`** — it loads only fully-resolved field defs. An unknown / malformed
  `$ref` **fails HARD** (the render aborts; a `$ref` must never leak).
- **The base config stays TEXT.** This is a LOW-RISK increment: only the
  **seam** is YAML-round-tripped (and only when it actually contains a `$ref`).
  `config.base.yml` is byte-unchanged and still spliced verbatim, so every
  load-bearing comment + verbatim-asserted base line (posts.summary, the format
  token, media_folder/public_folder, preview_context) is preserved.
- **Backward-compatible.** A seam with **no** `$ref` (inline fields — the status
  quo, e.g. adamdaniel's notes, jodidaniel's collections) is returned UNCHANGED
  by `expand_seam_text` and spliced exactly as before — **byte-identical**
  renders. Proven by diffing the new vs origin/main render of jodidaniel's real
  inline `collections.site.yml`.
- **Spec-locked** by `theme/spec/field_library_resolution_test.rb` (the resolver:
  single + multi-field refs, deep-copy isolation, hard-fail on unknown/malformed)
  + `e2e/field-library-ref-render.test.js` (drives `render-decap-config.rb` on a
  `$ref` fixture → resolved output, no `$ref` leak, base unchanged, hard-fail,
  no-ref backward-compat). The `$ref`-render spec reads platform `scripts/` +
  `theme/` source, so it's registered in `PLATFORM_META_SPECS` (playwright.config.js).
- **OUT OF SCOPE / future work:** the full base-collection-override **deep-merge**
  (a site overriding/reordering a base collection's fields) is deferred. Today
  the seam is still **append-only** (collections are spliced after the base);
  `$ref` only delivers shared-field REUSE, not base override.

### base_collections-aware spec skips for single-page consumers (#33, v0.1.9+)

Many e2e specs assume the generic collections (`posts/tags/projects/pages/e2e`)
+ adamdaniel-shaped content (`_posts/`, `_e2e/canary-*.md`, the rendered
`posts`/`tags`/… admin collections, `/blog/`, `/tags/`, `_site/e2e/canary-*/`).
A `base_collections: []` single-page consumer (jodidaniel.com) has **none** of
those, so those specs used to be **permanently RED** on every branch. The fix:
each generic-collection/content-dependent spec **self-skips PRECISELY** when the
consumer genuinely lacks that collection/content, and **runs fully** where it
exists (the platform `e2e/fixture-site` + adamdaniel.ai).

**The helper: `e2e/site-capabilities.js`** — the single source of truth for
"does THIS consuming site have X?". All predicates take an explicit `siteRoot`
(defaulting to `process.env.SITE_ROOT || <harness>/..`, the same root the rest
of the harness uses). Parses YAML with the real `yaml` lib.

- `keepsBaseCollection(siteRoot, name)` — **SOURCE** signal off `_config.yml`
  `cms.base_collections` (build-INDEPENDENT). Use this for **served-site**
  specs (they also run in the preview/prod `@parity` lanes, where `_site` is
  NOT built — a rendered-config check would wrongly skip a full consumer there).
- `hasAdminCollection(siteRoot, name)` / `adminCollections(siteRoot)` —
  **RENDERED** signal off `_site/admin/config.yml` (the ground truth Decap
  loads). Use this for **fs specs that already only run in the local lane**
  (they read `_site`, so the build is guaranteed present).
- `hasE2ECanaries(siteRoot)` / `hasRenderedCanary(siteRoot, slug)` /
  `hasSourcePosts(siteRoot)` / `isSinglePageConsumer(siteRoot)` — canary +
  posts presence.

**The skip pattern** — a precise `test.skip()` (or `beforeEach` skip) keyed on
the helper, with a message that names the collection + `cms.base_collections` +
`(#33)`:

```js
const cap = require("./site-capabilities");
test.skip(
  !cap.hasAdminCollection(SITE_ROOT, "posts"),  // fs/local-lane spec
  'consumer opts out of the "posts" collection via cms.base_collections — skipping <X> (#33)',
);
// served-site spec (also runs preview/prod @parity) → use keepsBaseCollection:
test.skip(!cap.keepsBaseCollection(SITE_ROOT, "tags"), "…opts out of tags… (#33)");
```

**Never weaken assertions for full consumers** — guard with a skip, don't relax
an `expect`. A full consumer that LOST its posts is a real failure, not a skip.
Specs that assert ABSENCE (e.g. sitemap "no draft / no `_e2e` canary leaks")
stay correct (empty) on an opted-out site and are intentionally NOT guarded.

**Guarded specs — group 1 (read-only / config / served-content):**
`canary-content.test.js`, `canary-ondemand-noindex.test.js`,
`cms-config.spec.js` (per-collection), `cms-post-list-summary.spec.js`,
`cms-permalink-contract.spec.js` (per-collection), `cms-preview-url.spec.js`
(per-collection — the Posts `preview_path` block is stripped on opt-out),
`cms-form-clarity.spec.js` (per-collection — every PROD_HINTS key is a base
collection), `sitemap.spec.js` ("every published `_posts` appears"),
`tags.spec.js` ("Tags index page"), `feeds-and-share.spec.js` (global Atom-feed
shape), `console-clean.spec.js` (`/blog/` + `/tags/` crawl URLs). These read the
RENDERED `_site/admin/config.yml` per base collection and self-skip inline on
`cap.hasAdminCollection(SITE_ROOT, "<name>")` (the rendered ground truth) — NOT
the registry `guard()`; the served-content specs self-skip on
`cap.keepsBaseCollection` (they also run the preview/prod `@parity` lanes where
`_site` isn't built). Several content-reading specs were also made
**SITE_ROOT-aware** (read `_posts/`, `_e2e/`, `_site/` under `SITE_ROOT`, not
`__dirname/..`) so they resolve the CONSUMING site's content; the two are
identical in a real consumer (harness at site root) but differ when the
meta-test points `SITE_ROOT` at a fixture.

> **The `@parity-preview` lane MUST export `SITE_ROOT` (#42, v0.1.15).** The
> served-content specs key their single-page skip on
> `cap.keepsBaseCollection(SITE_ROOT, …)`, which reads the CONSUMER's
> `_config.yml`. In the `parity-preview.yml` reusable the harness is checked out
> into `.cms-platform/`, so `SITE_ROOT || __dirname/..` resolves to the
> **platform** checkout (whose fixture `_config.yml` keeps all five base
> collections) unless the spec-run step sets `SITE_ROOT: ${{ github.workspace }}`
> (the first, default-path SITE checkout). Without it, a single-page consumer's
> parity lane crawls `/blog/` + `/tags/` and 404s (jodidaniel.com #35). The
> `e2e-tests.yml` lane already sets `SITE_ROOT` for `target==local`; the
> parity-preview lane now sets it too. **(Resolved — was a "latent gap to watch":
> `e2e-tests.yml` used to leave `SITE_ROOT=''` for `target` preview/prod; it now
> sets `${{ github.workspace }}` unconditionally, and the WHOLE `.cms-platform/e2e`
> harness family is covered — see the UNIVERSAL RULE note below.)** Locked by
> `e2e/parity-preview-site-root.test.js` (this lane) +
> `e2e/loop-site-root-lint.test.js` (the whole family).

> **THE UNIVERSAL RULE — every `.cms-platform/e2e` harness run MUST export
> `SITE_ROOT: ${{ github.workspace }}` (#1815, v0.1.22) — the realized "latent
> gap" above.** When a reusable checks the platform out into `.cms-platform/` and
> runs `npx playwright test` from `.cms-platform/e2e`, a base_collections /
> single-page guard's `SITE_ROOT || __dirname/..` fallback resolves to the
> **platform** checkout (which keeps all five collections) → the guard never
> fires. On jodidaniel.com (`base_collections:[]`) this made the host loop run
> `cms-delete-published.spec.js` and time out 60s on the `/^Posts$/` sidebar link
> the bio admin never renders. **Why `github.workspace` is always correct:** it is
> the site-under-test (default-path) checkout in EVERY lane — a no-op on the
> platform's own self-CI (where `github.workspace` and `.cms-platform` are the
> same tree) and on a full consumer (which keeps every collection); it only
> changes behaviour on a single-page consumer, where it makes the guards fire
> CORRECTLY. There is never a reason to resolve site config from the
> `.cms-platform` harness checkout, so an empty (`|| ''`) or platform-pointing
> value is always a bug.
>
> The rule is now enforced on the WHOLE family, not just the loops: the five loop
> reusables (`cms-publish-loop-host` / `-prod` / `-preview`, `cms-media-roundtrip`,
> `cms-preview-loops`), plus `canary-prod`, `cms-delete-published-preview`,
> `preview-media`, `visual-regression`, `e2e-tests` (its non-local lane used to
> emit `SITE_ROOT=''` — the realized latent gap, now `${{ github.workspace }}`
> unconditionally), and `parity-preview`. **Locked AS EARLY AS POSSIBLE by
> `e2e/loop-site-root-lint.test.js`** — a pure-fs lint in self-CI's
> `node-unit-lints` lane (no build / no browser, hard-fail), so a missing
> SITE_ROOT is caught at PR static-analysis time, *before* any loop ever runs
> against a live site. The lint scans every workflow and auto-covers ANY new
> reusable that grows a `.cms-platform/e2e` harness run — add the reusable, the
> lint demands its SITE_ROOT. (`preview-media` / `visual-regression` specs don't
> read SITE_ROOT today, but the rule is uniform and future-proofs a later guard.)

> **The closed blind spot (#34):** `cms-preview-url.spec.js` +
> `cms-form-clarity.spec.js` READ the rendered admin config per base collection
> but DON'T navigate index-local, so the original guard-registry detector (which
> only matched index-local route-hashes + sidebar-link waits) MISSED them — they
> red-failed a built single-page consumer despite the registry being green. The
> detector is now **comprehensive** (CLASS A/B/C below) so this whole class can't
> be missed again.

**Guarded specs — group 2 (CONSUMER-RUNNING admin-write/read/screenshots that
drive `/admin/index-local.html`):** these navigate
`#/collections/{posts,projects,pages,tags}/...` or wait for a base-collection
sidebar link, so on a `base_collections: []` consumer they would time out (the
local admin shows NO collections — see the config-local nuance below). They are
guarded via the **registry** `e2e/base-collections-guards.js` (single source of
truth, build-INDEPENDENT `keepsBaseCollection`), applied inline as
`test.skip(...guard(SITE_ROOT, "<basename>"))` at the top of each describe:

| spec | guarded on |
| --- | --- |
| `cms-smoke.spec.js` | **all** of posts/tags/projects/pages (hard-asserts the full sidebar) |
| `manual-walkthrough-contributor.spec.js` | **all** of posts/tags/projects/pages (asserts the full sidebar) |
| `cms-page-crud.spec.js` | `pages` |
| `cms-project-crud.spec.js`, `cms-project-gallery.spec.js` | `projects` |
| `cms-featured-image-lifecycle.spec.js`, `cms-html-embed.spec.js`, `cms-image-upload.spec.js`, `cms-inline-image.spec.js`, `cms-link-crawler.spec.js`, `cms-publish-flow.spec.js`, `cms-posts-list-runtime.spec.js`, `manual-walkthrough-content-guide.spec.js`, `manual-walkthrough-first-post.spec.js` | `posts` |

Specs that drive `/admin/index-test.html` (`config-test.yml` is FIXED, NOT
opted-out — `admin-no-occlusion`, `cms-mobile-layout`, `cms-editorial-workflow`,
`cms-field-targeting`, `cms-native-view-live`, …) must **NOT** be guarded. The
drift lint distinguishes them by the index-local route / sidebar-wait signal.

**The config-local single-page limitation (known):** the gem's
`decap_config_hook.rb` applies the `base_collections` keep-list deletion to BOTH
`config.yml` AND `config-local.yml`, but `config-local.base.yml` has **no
`__SITE_COLLECTIONS__` marker**, so a single-page consumer's **LOCAL-dev**
`/admin` (decap-server) shows **NO collections at all** — not even its own custom
ones (which DO appear in the prod `config.yml` via the marker). jodidaniel uses
the **prod github backend**, so this is local-dev-only; the #33 skips handle the
e2e impact. If a single-page consumer ever needs local-dev admin editing of its
custom collections, add a `__SITE_COLLECTIONS__` marker to `config-local.base.yml`
(follow-up — not done here).

**The two fixtures (the platform's own both-paths proof):**
`e2e/fixture-site` keeps every base collection + the 3 canonical canaries (the
FULL consumer); `e2e/fixture-site-singlepage` sets `cms.base_collections: []` +
one custom `notes` collection, NO `_posts`/`_e2e` (the OPTED-OUT consumer,
jodidaniel's shape). **Spec-locked** by THREE tests:

1. `e2e/site-capabilities.test.js` — the predicates against both fixture shapes.
2. `e2e/base-collections-skip-meta.test.js` — **build-and-run** proof: builds
   BOTH fixtures, subprocess-runs the **fs-guarded** specs against each, asserts
   opted-out → SKIPS, full → RUNS. Build-dependent → in `node-unit-lints`' DENY
   list (self-ci.yml) + `PLATFORM_META_SPECS`, so **no platform PR lane runs it**.
3. `e2e/base-collections-guard-registry.test.js` — the **pure-fs PR GATE**
   (CONCERN B). Runs in `node-unit-lints` (it's a hermetic `*.test.js`). It is
   the real protection on the admin-write + rendered-config guards: (a)
   **predicate proof** — for every registered spec, `shouldSkip(singlepage)===
   true` & `shouldSkip(full)===false` against the fixtures' `_config.yml` (no
   build); (b) **guard presence** — each registered spec actually imports the
   registry + calls `guard()/shouldSkip()` with its own basename; (c) **no silent
   drift (COMPREHENSIVE)** — its detector flags EVERY consumer-running spec that
   depends on a base collection existing, by ANY of three classes, and each
   flagged spec must be guarded (registry guard OR a direct inline
   `cap.hasAdminCollection`/`cap.keepsBaseCollection` self-skip) or in the
   `NON_GUARDED` allowlist, else RED:

   | class | signal | breaks on opt-out because |
   | --- | --- | --- |
   | **A** index-local route | `page.goto(…index-local.html#/collections/<base>)` | route never renders (collection stripped from `config-local.yml`) |
   | **B** index-local sidebar | `getByRole("link",{name:/^<base>$/i})` in a file that loads `index-local` but NOT `index-test` | sidebar link never appears |
   | **C** rendered-config per-collection | reads the rendered `_site/admin/config.yml` (`RENDERED_CONFIG`/`hasAdminCollection`/`adminCollections`) AND a per-base assertion: `preview_path`, a hint snapshot (`hintFor`/`PROD_HINTS`), `findCollection(cfg,'<base>')`, or `hasAdminCollection(…, '<base>')` | the `posts/tags/projects/pages/e2e` block is stripped → null/absent |
   | **D** single-page SURFACE (#21) | **D1** `page.goto(/admin/reviews…)` + a review-DATA read (`.health-card`/`.stat-grid`/`WORKFLOW_FILES`/`regression.json`); **D2** `page.goto(/preview/?collection=pages\|projects)` or a `data-preview-layout="pages\|projects"` expect; **D3** the `@canary-readonly` tag or `canary-content` import + `.publicPath`; **D4** writes a `_posts/*.md` draft + asserts `/blog/` | the consumer ships none of: a CMS review subject (reviews), preview.md + per-collection content (preview shell), `_e2e/canary-*` (canary probe), or a posts/`/blog/` surface (draft isolation) |

   It also has **detector-stays-comprehensive** tests anchored on
   `cms-preview-url` + `cms-form-clarity` (CLASS C) and the CLASS D set
   (`admin-reviews-{health,stats}`, `preview-shell`, `cms-publish-loop{,-preview}`,
   `cms-preview-pr-self-contained`, `draft-isolation`): if the detector regresses
   so it stops flagging any of these, that goes RED. A **precision-boundary** test
   asserts the detector does NOT flag the single-page-COMPATIBLE lookalikes —
   `glow-banding` (samples the THEME background on `/`; runs fine on a single-page
   bio), `admin-reviews-auth` (drives `/admin/reviews/` but only the site-AGNOSTIC
   OAuth handshake, no review data), `preview-bridge` (only regex-matches the URL
   its builder helper returns, never navigates a variant). A spec whose admin
   shell is `index-test.html` (`config-test.yml` is FIXED — not opt-out-deleted)
   is NOT flagged by A/B and must NOT be guarded. Because (2) never runs on a
   platform PR, (3) is what actually keeps the guard set from regressing.
   `NON_GUARDED` is **empty by design** (every flagged spec is guarded) and the
   stale-entry test requires any future entry to be genuinely
   flagged-but-unguarded.

#### The two guard registries in `e2e/base-collections-guards.js` (#33 + #21)

`shouldSkip(siteRoot, basename)` dispatches on the entry shape:

- **`ADMIN_WRITE_GUARDS`** (#33) — per-collection keep-list guards keyed on
  `keepsBaseCollection(siteRoot, name)` with `mode: "all"|"any"`. The CLASS A/B
  index-local navigators + **`draft-isolation.spec.js`** (posts: it writes a
  `_posts/*.md` draft + asserts `/blog/`, machinery a `base_collections:[]`
  consumer ships none of).
- **`CAPABILITY_GUARDS`** (#21) — coarse single-page guards keyed on a named
  capability predicate (`CAPABILITY_PREDICATES`): `isSinglePage` (→
  `isSinglePageConsumer`) or `hasE2ECanaries` (→ `!hasE2ECanaries`). Members:
  **`preview-shell`** + **`admin-reviews-health`** + **`admin-reviews-stats`**
  (`isSinglePage` — a static bio ships no preview.md / has no review subject),
  **`cms-publish-loop`** (its `@canary-readonly` probe) + **`cms-publish-loop-preview`**
  + **`cms-preview-pr-self-contained`** (`hasE2ECanaries` — no `_e2e/canary-*` to
  drive). Apply inline as `test.skip(...guard(SITE_ROOT, "<basename>"))`.

The two registries are **disjoint** (a spec is guarded by exactly one). The
guard-registry lint proves the both-directions predicate (`shouldSkip(single)===
true & shouldSkip(full)===false`) + guard presence for BOTH. **The reviews
dashboards were also de-identified**: they read `window.CMS_REPO`/`CMS_APEX`, so
the mocked GitHub-API + `regression.json` routes match ANY owner/repo/apex (not a
hardcoded `adamdaniel.ai`); `preview-shell` reads the expected `.site-logo` from
`_config.yml` `title`, not a literal "Adam Daniel". This is what lets the FULL
fixture (and every consumer) RUN+PASS them, while the single-page fixture SKIPS.
**glow-banding is intentionally NOT guarded** — investigation showed it samples
only the theme background gradient on `/`, which renders identically on a
single-page bio (it passes on both fixtures); guarding it would skip a real
glow/theme regression on a single-page consumer.

**Adding a NEW generic-content spec:**
- **Read-only / served / fs spec** (reads a base collection / canary / posts /
  `/blog/` / `/tags/`): guard on the matching `site-capabilities` predicate
  (rendered for local-only fs specs, `keepsBaseCollection` for served specs that
  also run `@parity`), and add `/^e2e\/site-capabilities\.js$/` to its
  `SPEC_RULES` entry in `select-specs.js`. **If it reads the rendered
  `_site/admin/config.yml` per base collection** (CLASS C — `preview_path`, a
  hint snapshot, `findCollection(cfg,'<base>')`, …), the guard-registry detector
  will flag it; you MUST apply a direct inline `cap.hasAdminCollection(SITE_ROOT,
  "<name>")` self-skip (mirror `cms-config.spec.js` — gate the per-collection
  assertion, not the whole file, where a spec mixes collection-specific +
  agnostic checks) or the drift gate goes RED. No registry entry is needed for
  CLASS C — the inline `hasAdminCollection`/`keepsBaseCollection` self-skip is
  what the detector recognizes as coverage.
- **CONSUMER-RUNNING spec that drives `/admin/index-local.html`** and navigates a
  base collection (route `#/collections/<base>` OR a base-sidebar-link wait):
  you MUST (1) add an entry to `ADMIN_WRITE_GUARDS` in
  `e2e/base-collections-guards.js` (its collection(s) + `mode: "all"|"any"` +
  a `(#33)` reason), (2) apply the inline guard
  `test.skip(...guard(SITE_ROOT, "<basename>"))` at the top of the describe
  (`const { guard } = require("./base-collections-guards")`,
  `const SITE_ROOT = process.env.SITE_ROOT || path.resolve(__dirname, "..")`),
  and (3) add `/^e2e\/site-capabilities\.js$/` + `/^e2e\/base-collections-guards\.js$/`
  to its `SPEC_RULES` entry. If you DON'T want a guard (the spec drives
  `index-test.html`, or does no collection nav), the drift lint will go RED until
  you either register it or add it to the lint's `NON_GUARDED` allowlist with a
  reason. **`base-collections-guard-registry.test.js` enforces all of this** — you
  can't merge an unguarded generic index-local spec.

> **Guard EVERY `test()` in a multi-test guarded spec, not just one (v0.1.23).**
> The guard-presence check is satisfied by the inline guard appearing ANYWHERE in
> the file — which let `cms-publish-loop.spec.js` ship its `@canary-readonly` test
> guarded while the MAIN `@admin-write` host-loop `test()` (it drives the canary
> through the live admin) carried NO guard. On jodidaniel.com (no `_e2e/canary-*`
> → `hasE2ECanaries` false) the unguarded test RAN and timed out 60s on "Confirm
> baseline is live" waiting for `/e2e/canary-post/` (404 on a bio) — red even
> AFTER the SITE_ROOT fix (#58), because that test's canary nav uses a VARIABLE
> collection (`#/collections/${CANARY.cmsCollection}`) the per-file detector
> never pattern-matched. **Rule:** every top-level (column-0) `test()` block in a
> guarded spec MUST carry its own `test.skip(...guard(SITE_ROOT, "<basename>"))`.
> Locked by the per-block assertion in `base-collections-guard-registry.test.js`
> ("every top-level test() block in a guarded spec carries the inline guard").

### Org OAuth App approval — the "can log in but can't save" trap (#26)

On an **org-owned** consumer, if the org has **OAuth App access restrictions**
enabled and the CMS OAuth App isn't approved for the org, Decap authenticates +
reads but every **persist fails** with `OAuth App access restrictions`. An org
owner approving the app fixes it (jodidaniel#27, resolved). **Spike result —
trust it:** there is **no public GitHub API** to ask "is OAuth App `<client_id>`
approved for org `<org>`?" (org OAuth-App authorizations aren't exposed like
GitHub App installations), and a **PAT write-probe FALSE-GREENS** (the
restriction targets the OAuth App's user-token flow, not a PAT). So **do NOT add
an API approval-check or a PAT probe.** The shipped, practicable subset:

- `theme/admin/oauth-app-restriction-detector.js` — admin shim that **observes
  Decap's notification DOM** (MutationObserver) for the restriction text and
  shows a **dismissible** banner pointing the org owner at *Settings →
  Third-party access → OAuth App policy*. It **must not** wrap `window.fetch`
  (publish-via-auto-merge.js already does — a second wrap risks the Safari
  loadEntries hang). It exposes pure helpers on
  `window.OAuthAppRestrictionDetector` (`isOAuthAppRestrictionError`,
  `orgFromRepo`, `orgOAuthPolicyUrl`) and is **requireable in Node** (DOM
  wiring guarded by `typeof window/document`). **Loaded PROD-ONLY** (in
  `theme/admin/index.html`, after `posts-list-enhance.js`) — only the real
  github backend can produce the error; it's inert elsewhere. It's
  **order-independent** of the `live-url-derive → banner → native-preview-href →
  posts-list-enhance` chain the load-order spec locks (`cms-posts-list-enhance.spec.js`).
- `scripts/preflight-oauth.js --repo OWNER/REPO` — org-owner go-live CLI;
  detects owner type via `gh`, prints org-approval guidance (org) or "no
  approval needed" (user); resilient when gh is absent. Pure helpers
  (`parseRepo`, `messageFor`) exported for tests.
- `scaffold/create-site.js` nextSteps carries a conditional org-OAuth reminder.

Tests: `e2e/oauth-app-restriction-detector.test.js` (pure helpers, Node) +
`e2e/oauth-app-restriction-detector.spec.js` (`@admin-read` runtime banner,
simulates the Decap error toast — no backend needed) +
`e2e/preflight-oauth.test.js`.

## Single-version pin consistency guard (anti-skew, #29)

A consumer references the platform version in MANY places (every reusable
`uses: …/.github/workflows/<n>.yml@<ref>`, every SHA-pinned composite
`uses: …/.github/actions/<n>@<sha>  # vX.Y.Z` COMMENT, the `Gemfile`/`Gemfile.lock`
`tag:`, and `platform.lock` `platform_ref`). Dependabot + `platform-bump` land
bumps PIECEMEAL, so consumers drift (observed live: adamdaniel.ai pinned `@v0.1.0`
loop/deploy callers, gem `@v0.1.5`, others `@v0.1.3`/`@v0.1.6` at once — a `v0.1.0`
reusable against a `v0.1.5` gem is a latent bug source). **`platform-bump.yml`
rewrites `.github/workflows/*` and pushes, so its token (`CMS_PLATFORM_PAT`)
MUST carry `workflow` scope** or GitHub rejects the push (`refusing to allow …
to update workflow … without 'workflows' permission`) — the live half of #13.
It also seeds any workflow caller the release newly made platform-dictated —
copying the missing caller from `examples/site/.github/workflows/` at the new
ref, re-pinned to it — so the workflow-set-parity check (introduced v0.1.20,
#54) also passes on the bump PR alone. Observed live: v0.1.54 added
`dependabot-rearm-sweep.yml` and both consumers' bump PRs failed pin-consistency
with `workflow-set: MISSING (platform-dictated)` until hand-fixed.

`scripts/check-platform-pin-consistency.js` (platform-owned, Node, needs only the
repo's `yaml` lib) makes them all agree:

- **Canonical version = `platform.lock` `platform_ref`** (source of truth; missing/
  unparseable → hard fail with a clear message).
- Parses every `.github/workflows/**/*.yml` with the **`yaml` parser** (anchors
  resolved — NOT regex); collects `uses:@` refs targeting the platform owner/repo
  (configurable via `--owner/--repo`, defaulting from `platform.lock`
  `platform_repo`). Reusable refs `.../workflows/*.yml@<ref>`: the `<ref>` must ==
  `platform_ref`. Composite refs `.../actions/*@<sha>`: SHA-pinned, so the gate is
  the trailing `# vX.Y.Z` COMMENT == `platform_ref`. **The comment is read by a
  LINE-AWARE pass** because the YAML parser drops comments — the one justified
  regex/line exception (same rationale as `scripts/sync-action-pin-comments.sh`,
  documented in the script header).
- Reads `Gemfile` (`gem "cms-platform-theme", …, tag:`) + `Gemfile.lock` (the
  cms-platform GIT-source `tag:`); both must == `platform_ref`. Tolerates a
  consumer with NO Gemfile; ignores non-cms-platform `uses:`.
- **Aggregates ALL** violations (doesn't stop at first); prints a precise per-file
  report (file + found + expected) + `::error file=` annotations under
  `GITHUB_ACTIONS`. Exit non-zero iff any mismatch; exit 0 + OK summary otherwise.

Reusable + thin caller: `.github/workflows/platform-pin-consistency.yml`
(`workflow_call`; mirrors `platform-drift-guard`'s checkout-consumer +
checkout-platform-at-`platform_ref`-into-`.cms-platform/` + run-platform-script
shape; the reusable `npm install --no-save yaml` before running, since the script
resolves `yaml` from cwd/node_modules) + `examples/site/.github/workflows/...`
(`pull_request`, NO `paths:` filter — any pin-bearing file can skew). Self-test:
`e2e/check-platform-pin-consistency.test.js` (`@lane local`, runs in
node-unit-lints) — consistent fixture → 0; skewed fixture → non-zero, each
offending file/value named. **Complements** `platform-drift-guard` (that guards
file CONTENT byte-match; this guards VERSION CONSISTENCY). See `docs/SYNC.md`
"Single-version pin invariant".

The same guard also enforces **workflow-content (call-interface) parity**
(companion to the workflow-SET parity): a consumer's thin caller must match the
canonical `examples/site` template's CALL INTERFACE — each job's `uses` target +
`with` KEY-set + `secrets:` map + permissions — modulo version refs, site-specific
`with` VALUES, and deliberately site-tuned `on:` triggers (all
normalized/masked/excluded). The version-pin checks compare only the `@ref`
STRINGS, so they were BLIND to a caller whose BODY drifted — e.g. jodidaniel's
sweep caller silently dropped the now-required `secrets: CMS_E2E_PAT:` map and
`startup_failure`'d the reusable for weeks. `checkWorkflowContentParity()` parses
both callers (comments/formatting drop out), compares the call interface, and
flags the exact drifting facet. It does NOT fight a legit site difference (e.g.
adamdaniel TRIMS the host-loop push `paths:` to dodge prod-loop co-arrival
eviction #1892 — an `on:` change, excluded).

## Consumer-context spec rule (v0.1.5)

The e2e harness is **reused by consumers**. `e2e/playwright.config.js` runs in
CONSUMER mode when `process.env.SITE_ROOT` is set (the consuming site is built +
served from `SITE_ROOT`); the `PLATFORM_META_SPECS` list is then `testIgnore`'d
(those specs assert the platform's OWN source tree).

**A spec that RUNS in consumer mode MUST NOT read admin from the platform
SOURCE tree (`theme/admin`)** — consumers have no `theme/admin`, only the
gem-RENDERED `_site/admin`. Read the **served bytes** instead:
`await (await page.request.get('/admin/<file>')).text()`, or read
`path.join(SITE_ROOT, '_site', 'admin', '<file>')` (pattern in
`cms-config.spec.js`). `preview-bridge.spec.js` regressed exactly this in v0.1.5
(it `readFileSync`'d `theme/admin/preview-bridge.js`, passing platform self-CI
but ENOENT'ing in every consumer run). **Guarded** by
`e2e/admin-spec-source-read-lint.test.js`: a non-meta `.spec.js` that reads
`theme/admin` or legacy `../admin` fails the lint; a genuinely platform-only
spec goes into `PLATFORM_META_SPECS` in `playwright.config.js` (the lint parses
that list out of the config so the two stay in lockstep).

### PLATFORM_META_SPECS registration is MANDATORY for platform-internal specs (#16)

A **platform-internal** spec validates the platform's OWN machinery, not a
consuming SITE's content/admin behavior. Concretely, its code (comments
stripped) reads at least one of: the platform `scripts/**` tree, `scaffold/**`,
the platform's OWN reusable **workflow DEFINITIONS** (via `workflow-yaml-utils` /
`readWorkflow()`, or an fs path into `../.github/workflows` or the
`examples/site/.github` templates), the `theme/**` SOURCE tree, or the platform
**fixtures** as a literal path (`fixture-site` / `fixture-site-singlepage`, not
via `SITE_ROOT`). **Every** such spec MUST be in `PLATFORM_META_SPECS` —
otherwise it RUNS on a `CONSUMER=true` e2e lane (where that source doesn't
exist) and red-fails. This bit the adamdaniel.ai v0.1.10 reconciliation: five
unregistered meta-specs (`workflow-loop-branch-cleanup`, `preflight-oauth`,
`check-platform-pin-consistency`, the two `scaffold-*`) ran+failed on the
consumer. The platform's own self-CI runs e2e with `TARGET=prod` (never the
`CONSUMER=true` lane), so an unregistered meta-spec ships GREEN on the platform
and only detonates on the next consumer.

Keep genuine **SITE** specs OUT of the list (sitemap/tags/feeds/console-clean/
cms-config/permalink/post-summary, the canary content invariants, the manual
walkthroughs, the real publish-loop round-trips). Those resolve their root
through `SITE_ROOT` and read the consumer's own built `_site/**` / content tree
(or self-gate on `site-capabilities`), so they MUST run on a consumer.

**Recurrence guard — `e2e/platform-meta-spec-registry.test.js`** (runs in
self-CI `node-unit-lints`). It statically classifies every spec by the
platform-internal signals above and FAILS if any platform-internal spec is NOT
in `PLATFORM_META_SPECS`. The detector is **path-name-agnostic** — it keys off
the `scripts/` / `scaffold/` / `theme/` / `.github/workflows` SUBPATH literal no
matter how the prefix var is spelled (`REPO_ROOT`, `__dirname`, …), because
`cms-config-preview-delta.spec.js` execs `path.join(REPO_ROOT, "scripts/…")`
which a naive `../scripts`-only matcher missed. This makes "I forgot to register
a meta-spec" impossible to ship — mirrors the `base_collections` guard registry.
When you add a platform-internal spec, register it; when the guard goes RED, add
the named spec to `PLATFORM_META_SPECS` (or, if it only LOOKED internal because
it read `${SITE_ROOT}/_site/**`, make it read via `SITE_ROOT` — not a `../scripts`
/ `../scaffold` / `../theme` / `../.github/workflows` source path).

## Editorial-workflow label audit (v0.1.6; self-heal + label-at-creation v0.1.48)

Decap re-runs its editorial-workflow label migration on **every** `/admin` load
(the persistent "Decap CMS is adding labels to N of your Editorial Workflow
entries" dialog) when an open editorial PR (a `cms/*` branch) is **missing** its
`decap-cms/<draft|pending_review|pending_publish>` label — repo-wide, so it
shows on prod AND every preview deploy. Guards:

- `e2e/cms-editorial-label-migration.spec.js` — drives the in-browser test-repo
  backend; asserts the dialog is ABSENT, or gone after dismiss + 30s + reload
  (never survives that cycle).
- `scripts/audit-editorial-labels.js` — flags open `cms/*` PRs missing a
  `decap-cms/<status>` label; exits non-zero with `::error::` annotations.
  With `--fix` (the reusable's default since v0.1.48) it SELF-HEALS instead:
  applies `decap-cms/pending_publish` when the PR carries `cms/ready` (it is
  literally queued to publish), else `decap-cms/draft`, and only exits
  non-zero when a fix didn't stick — a red audit now means "needs a human".
  Motivation: the flag-only audit went red daily for a week (PR #2387,
  2026-07) while the "adding labels…" dialog sat on prod — scheduled-run
  failures are invisible, so detect-only was the wrong contract.
- `.github/workflows/editorial-label-audit.yml` — reusable; consumers wire a
  daily-cron caller (sparse-checks out just the audit script from the platform). It
  MUST pass `--repo ${{ github.repository }}` (v0.1.16): the sparse checkout
  leaves no git repo in `github.workspace`, so a bare `gh pr list` fails
  `not a git repository`. Self-heal needs `pull-requests: write` from the
  CALLER (reusable permissions are capped by the caller's grant); with only
  `read` the fix 403s and falls back to failing loud. Lint-locked by
  `e2e/editorial-label-audit-repo.test.js`.
- **Label at creation (v0.1.48):** every non-Decap writer that opens a `cms/*`
  PR applies `decap-cms/pending_publish` alongside `cms/ready` so the
  migration never has a target in the first place — the publish-via-auto-merge
  shim's delete-recovery PRs, `cms-fixture-pr.js` seed/remove fixture PRs, and
  `sweep-stale-cms-prs.yml`'s two cleanup PRs. (Decap-created editorial PRs
  label themselves.) The pre-v0.1.48 "`cms/e2e-fixture/remove-*` PRs
  transiently red the audit — expected churn" caveat is obsolete: those PRs
  are labelled at creation now, and the audit heals any stragglers.

## Dependabot batch-strand re-arm sweep (#118-122 postmortem)

`self-dependabot-auto-merge.yml` (→ the reusable `dependabot-auto-merge.yml`)
only fires on `pull_request`, so it arms native GitHub auto-merge
(`gh pr merge --auto --squash`) exactly once per PR, the moment Dependabot
opens it. That is enough for a SINGLE Dependabot PR, but not for a BATCH: when
Dependabot opens several PRs against the same base in one run (observed live,
2026-06-30: cms-platform #118-#122), the first PR(s) merge and advance `main`,
and GitHub responds by AUTO-DISABLING auto-merge on every remaining PR in the
batch (PR #121's timeline: `auto_merge_disabled` by `github-actions[bot]` at
19:06:03, 46 seconds after `auto_merge_enabled` fired). Nothing re-arms
them — no further `pull_request` event ever arrives for a PR nobody pushes to
again — so a green, conflict-free, fully-mergeable PR strands indefinitely.
#121 and #122 sat `CLEAN` for 6 days until merged by hand.

**Fix — a scheduled re-arm sweep**, mirroring the `sweep-stale-cms-prs.yml` /
`regression-review-reaper.yml` shape (pure-`gh`-API scheduled job, no
per-PR checkout):

- **`dependabot-rearm-sweep.yml`** (reusable, `workflow_call`) lists every OPEN
  `dependabot[bot]` PR (`gh pr list --author app/dependabot`); for each with
  ALL checks green (`statusCheckRollup` non-empty, no non-SUCCESS/NEUTRAL/
  SKIPPED entry) and `mergeable == MERGEABLE`, it re-validates the SAME
  manifest-path allowlist `dependabot-auto-merge.yml` enforces, then merges:
  **directly** (`gh pr merge --squash`, no `--auto`) when GitHub already
  reports `mergeStateStatus == CLEAN` — avoids re-entering the same
  auto-disable race — otherwise **re-arms** auto-merge (`--auto --squash`) so
  GitHub finishes the job once its own bookkeeping catches up. Same-repo only
  (Dependabot branches are never forks), so the default `GITHUB_TOKEN`
  suffices — no PAT.
- **The manifest-path allowlist is factored into `scripts/check-dependabot-
  manifest-paths.sh`**, the single source both `dependabot-auto-merge.yml`
  (the per-PR `pull_request` gate) and `dependabot-rearm-sweep.yml` (the
  sweep) call — keep the two call sites in lockstep; a change to the
  allowlist changes behaviour identically for both.
- **`self-dependabot-rearm.yml`** dogfoods the sweep on cms-platform's own
  Dependabot PRs (daily cron + `workflow_dispatch`), same pattern as
  `self-secrets-scan.yml` / `self-dependabot-auto-merge.yml`. A consuming site
  adopts it via the thin caller
  `examples/site/.github/workflows/dependabot-rearm-sweep.yml` — the same
  batch-strand exposure applies to every consumer that calls
  `dependabot-auto-merge.yml`.

## Scheduled-run health audit (silent-failure alerting, v0.1.57)

Scheduled workflows fail SILENTLY — an `event=schedule` failure has no PR to
go red on and fires no notification. Observed live (the 2026-07 audit that
motivated this): adamdaniel.ai's daily editorial-label-audit was red 24/30
days for three weeks unnoticed; jodidaniel.com's sweep-stale-cms-prs
startup-failed 30/30 for a month (a dropped `secrets:` map). The alerting
layer:

- **`.github/workflows/scheduled-run-health.yml`** (reusable) — daily scan of
  the CALLER repo's last `window_hours` (default **48h**) of schedule-event
  runs for `failure` / `startup_failure` / `timed_out` (NOT `cancelled` — the
  loops cancel superseded runs by design). Findings land on **one** tracking
  issue (label `ci`, found via a hidden `<!-- scheduled-run-health-audit -->`
  marker): opened on first failure (the issue notification IS the alert),
  NEW runs commented with run-id dedupe (a hidden `<!-- run-ids: … -->`
  block keeps the dedupe exact past the 5-links-per-workflow display cap),
  auto-closed once a full window passes clean. Zero changes to the existing
  scheduled callers — it watches them all from the outside. Logic lives in
  `scripts/audit-scheduled-runs.js` (requireable; pure helpers exported),
  sparse-checked-out by the reusable, which passes
  `--repo ${{ github.repository }}` explicitly (no git repo in the workspace
  — the editorial-label-audit v0.1.16 trap).
- **Why 48h for a daily audit:** GitHub throttles crons on these repos
  (measured: `*/5` fires every 45-90 min; daily crons run 4-5h late), so two
  consecutive daily audit runs can be ~29h apart — a 24-25h window would
  leave a blind gap. The overlap can't double-report thanks to the run-id
  dedupe.
- **Exit-code contract:** the audit run stays GREEN when it successfully
  files/updates the alert (the issue is the channel); red means the audit
  ITSELF is broken (API/permission failure) — same "red needs a human"
  contract as `audit-editorial-labels.js --fix`. The audit is itself a
  scheduled workflow, so its own failed run is reported by the NEXT day's run.
- **Callers:** `self-scheduled-run-health.yml` dogfoods it on cms-platform
  (cron `47 8 * * *` + dispatch); consumers get
  `examples/site/.github/workflows/scheduled-run-health.yml` (auto-seeded by
  `platform-bump` since v0.1.55). Callers must grant `actions: read` +
  `issues: write`, and declare the dispatch `dry_run` as `type: string` +
  `fromJSON`-coerced (typed booleans startup-fail the handoff — the exact
  failure class this audit exists to catch). Lint-locked by
  `e2e/scheduled-run-health.test.js` (workflow shapes + the script's pure
  helpers; registered in `PLATFORM_META_SPECS`).

## E2E parallelism — one CI job per Playwright project (v0.1.68-v0.1.70)

`e2e-tests.yml` runs the suite as **one job per Playwright project**, each
installing only its own browser engine, each at `150%` workers. Machinery: **`e2e/ci-matrix.js`** derives the matrix list, each
job's engine, and each job's worker count from `playwright.config.js`;
**`e2e/ci-matrix.test.js`** fails self-CI if the workflow's static
`matrix.project` drifts from the real project list (the one way this design can
silently stop running a project). Full measurements + the rejected alternatives:
**`docs/E2E-PARALLELISM.md`** — read it before re-tuning any of this.

The three findings that shaped it, all measured on adamdaniel.ai:

- **Measure the worker count on the job shape you SHIP.** With 8 projects in one
  job, raising workers to `100%` made the SAME tests report 2.1x longer and the
  wall clock WORSE (263 s → 284 s) — which read as "a 4-vCPU runner saturates at
  2 browser workers". With ONE project per job the answer reverses: 6 workers
  (`150%`) beat 4 on the critical-path project (165 s → 130 s) and beat 2 on
  almost every public project. So every project job now runs at **`150%`**, one
  number for all of them (uniform measured no worse than a per-project table,
  and a table is a thing to maintain). It is deliberately NOT a blanket CI
  default in `playwright.config.js` — the other reusables run the whole matrix
  in ONE job, the shape where more workers measured worse.
- **`--shard` cannot balance this suite.** It balances by test COUNT while
  per-test durations span 5 ms → 49 s; a real 4-way shard measured
  80/105/88/**671** s. Hand-grouped lanes failed too (modelled 308/330/307,
  measured 220/236/**373** s — the 8-project public lane's cost is dominated by
  test COUNT, not duration). One job per project needs no cost table at all.
- **The 3-engine `install --with-deps` was 58 s of every job's critical path**
  (39 s apt + 19 s download). One engine per job removes most of it, needs no
  cache key, and can't go stale. **If you add a project, give it an explicit
  `use.browserName`** (`engineFor()` throws otherwise) and add it to the workflow
  matrix (the lint will tell you).
- **EVERY harness-running step must declare `PW_PROJECT`** (one name or a
  comma-separated list) so `install-browsers-on-miss.js` narrows its
  missing-engine check to the engines actually in play. Without it the blanket
  check reports the engines that step never installed as "missing", downloads
  them for browsers the run never launches, and prints the ci-runner-drift
  warning — permanently, so a REAL drift is indistinguishable. That had been true
  of all ten sibling reusables AND the platform's own self-CI lint lane (which
  installs no browsers at all and was fetching all three): adamdaniel.ai
  canary-prod job 92842548516, cms-platform self-ci job 92855380065.
  **`e2e/engine-scope-lint.test.js` fails if a step's `PW_PROJECT` is missing or
  disagrees with its `--project` flags.**
- **NEVER shell out to a raw `npx playwright install` from a workflow** — use
  `.github/actions/install-playwright-browsers`, which splits the install into
  TWO phases, each retried up to 3 times: `install-deps` (the apt half) and
  `install` (the browser download, no `--with-deps`). `--with-deps` apt-installs
  ~90 packages first, and on 2026-08-07 the Ubuntu mirror served one runner at
  ~35 KB/s for its whole run, so the (then-combined) `install --with-deps webkit`
  took **39 minutes** while the tests it installed for took 41.6 s (adamdaniel.ai
  job 92862768030). Fanning out to ten lanes means ten INDEPENDENT apt exposures
  per run, and the aggregating `e2e` gate waits for the slowest — so that one
  lane held a delete-recovery PR open 40 min and blew the media-roundtrip loop's
  30-minute delete-leg budget. **Not rare:** a second run 67 min later did the
  same on a different lane (run 31181957723, `chromium-mobile`, 606 s install /
  20 s tests), so expect it on the order of one run in ten.

  **Only the download half is time-bounded — apt is retried but never wrapped in
  `timeout`, and that asymmetry is deliberate, not a gap.** The action's first
  version bounded the WHOLE `install --with-deps` call, and that didn't abandon a
  slow install, it *orphaned* one. `timeout` signals only the process it directly
  launched, but Playwright logs "Switching to root user to install
  dependencies..." before it shells out to apt — so the `apt-get` doing the real
  work is a **root-owned grandchild**. An unprivileged `timeout`'s signal to its
  own process group can't touch a root-owned process (EPERM) no matter how the
  process group is arranged, so `setsid` plus a group kill doesn't fix it either
  — **no signal-based kill can**, because the privilege gap, not the process
  grouping, is what blocks it. Measured on adamdaniel.ai job 92989057569:
  attempt 1's apt started fetching under its 420 s bound with zero lock-wait
  lines (it owned the dpkg lock cleanly); `timeout` killed attempt 1 mid-transaction
  at the bound; 19 seconds later attempt 2 died with "Could not get lock
  /var/lib/dpkg/lock-frontend. It is held by process 2857 (apt-get)" — that pid
  was attempt 1's own killed-but-surviving `apt-get`, not the runner's boot-time
  `apt-daily`, and every later attempt starved on the same orphan. So `apt`
  (`install-deps`) now runs with no `timeout` around it — retried on failure,
  never killed — while the download (`install`, no `--with-deps`) keeps the
  bound below. The trade is deliberate: apt IS the slow phase (the 39-minute
  incident above was package fetches, not the CDN), so one lane can still finish
  late; late-and-green beats red-and-blocked, because a red required check blocks
  a `cms/*` canary PR permanently instead of merging it late. A genuinely hung
  apt is now bounded only by the caller's own job `timeout-minutes`, where "job
  timed out" is an accurate report rather than a misleading one. `npx playwright
  install` also wraps apt's exit 100 as exit 1, so the outer status was never
  diagnostic on its own; classification now greps the captured output for
  `Could not get lock|lock-frontend|dpkg was interrupted` before looking at the
  exit code, so a lock failure on the unbounded apt phase is never misreported
  as a timeout.

  **Two wrong designs to avoid for the download half.** A bare
  `timeout-minutes:` converts a slow mirror into a RED required check, which
  blocks a `cms/*` canary PR permanently instead of merging it late. And a
  *uniform* retry bound does the same thing whenever the mirror is slow for the
  WHOLE run — the measured case needed 2340 s, so three 420 s attempts would all
  hit the bound and exit 1. So the download's budget **escalates**: short early
  attempts abandon a stalled connection fast, the LAST attempt gets 1200 s to
  actually finish, and the download resumes so attempts accumulate progress
  (apt's own `Acquire::*::Timeout` does nothing — the bytes were flowing, just
  slowly). The worst case must also stay under the caller's own
  `timeout-minutes`, or the job is killed mid-retry and reports an opaque "job
  timed out" instead of the diagnostic — `canary-prod`'s 10-minute probe passes
  smaller values for exactly that reason. These properties are locked by
  **`e2e/playwright-install-bounded.test.js`**.
  **And the most common apt failure is not slowness at all — it is losing the dpkg
  lock to the runner's own boot-time `apt-daily`,** which exits 100. Retrying cannot
  fix that when the attempts are back-to-back: all three land in the same lock
  window (measured, job 92892148211 — it failed the webkit lane, failed the `e2e`
  gate, BLOCKED the host loop's canary PR, and the loop then timed out waiting for a
  merge that could never happen). So the action also (a) drops
  `DPkg::Lock::Timeout` into `apt.conf.d` so apt WAITS for the lock — a drop-in
  because the apt-get that matters is inside `playwright install-deps`, which we
  never invoke directly — and (b) backs off between retries (15 s, 30 s). Same
  lint asserts both.
- **The reusable sets `DISABLE_PER_TEST_VIDEOS=1`.** `e2e/base.js` captures a
  full-page screenshot on every main-frame navigation of every test, and its only
  consumer (`e2e/generate-test-videos.js`) is invoked by no reusable — the
  adamdaniel-only `finalize` job that assembled the videos was never ported. So
  CI was paying for frames nothing reads, worst on the link-crawling admin specs.
  `screenshot: "on"` + `video: "retain-on-failure"` still produce the failure
  artifacts. If you ever wire the video assembly up, unset it there.

The required status context is **unchanged**: the matrix sits behind an
aggregating `e2e` gate job (`needs: project`, `if: always()`, fails on any
non-success matrix result), so rulesets and the `e2e-required-stub` companion
still name exactly `e2e / e2e`. Per-job artifacts and failure-comment markers
are project-scoped (`playwright-report-<project>`,
`e2e-failure-summary-<project>`) — jobs sharing either would clobber each other,
and a marker that names the project says which one went red before you open a log.

**Escape hatch:** the reusable's `workers` input overrides every job without a
release (`workers: "2"`), for the day a project turns flaky under load.

### Parallelism turns latent test-isolation bugs into real flakes

Running the admin projects wider exposed four PRE-EXISTING bugs (all fixed in
v0.1.68). Keep the pattern in mind when writing @admin-write specs:

- **A fixture basename shared between specs is a cross-spec FS race.** Decap
  names an uploaded asset after the basename it is handed, and three specs then
  globbed `assets/images/uploads/` for the SAME `tiny-pixel.png` — so
  `cms-image-upload`'s cleanup deleted `cms-featured-image-lifecycle`'s
  in-flight upload ("replace with B → A still on disk" saw 0 files). Use
  **`e2e/upload-fixture.js`** (`uploadFixture(source, basename)`) to hand each
  spec its OWN stable basename.
- **A test whose budget doesn't scale with its input will time out under
  contention.** `image-alt-text.spec.js` crawls EVERY sitemap URL in one test on
  Playwright's fixed 30 s default — already ~21 s at 2 workers. It now scales
  its budget with the URL count, like `cms-link-crawler.spec.js`'s explicit
  240 s crawl budget. The 30 s `actionTimeout` is what catches a genuine hang,
  so a generous *test* budget hides nothing.
- **A spec that drives `/admin/index-local.html` MUST carry an `@admin-*` tag.**
  Tag routing is opt-IN: an untagged test matches every public project's
  `grepInvert`, so a forgotten tag doesn't fail — it silently runs the Decap admin
  (and its writes, and its `jekyll build`) on all EIGHT public-lane projects.
  `cms-html-embed.spec.js` shipped that way. Locked by
  **`e2e/admin-tag-lint.test.js`**.
- **Never `existsSync`-then-read a file another process writes.** decap-server
  creates an entry file and then fills it, so `expect.poll(() =>
  fs.existsSync(file))` can win the race and read `""` — the "decap-server
  file-write race" `retries: 1` was added for. Poll the CONTENT with
  `contentOrEmpty()` from **`e2e/fs-poll.js`**, or `fileReady(<finder>)` when the
  path itself is discovered by a readdir helper. **This one bit twice:** v0.1.68
  converted five specs and left six behind, and two of THOSE feed the read
  straight into a `writeFileSync` of the same path — so an empty read did not
  merely fail an assertion, it overwrote the entry with front-matter-less content
  and left a corrupt page on disk for the retry. All eleven now poll content, and
  **`e2e/fs-poll-lint.test.js`** (AST) fails the build on the shape, so "the rule
  is written down" is no longer the only thing enforcing it. An existence poll for
  a file the spec never READS is fine and is not flagged.
- **A shared external tool needs a lock.** Nine specs shell out to
  `bundle exec jekyll build` against the same tree and the same `_site` the
  webServer serves; two overlapping builds fight over `_site` and one dies. They
  all go through **`e2e/jekyll-build.js`** now, which serialises them behind an
  atomic mkdir lock (cross-PROCESS — Playwright workers are separate processes)
  with a stale-holder break and a `finally` release, and it CREDITS the wait back
  to the caller's test timeout so the lock can't trade the build race for a
  timeout race (these specs run on Playwright's 30 s default). **Never shell out
  to `jekyll build` from a spec directly** — `jekyll-build.test.js` fails the
  build if you do. Two lock defects found by review and fixed in v0.1.70:
  **(a) `STALE_MS` must stay BELOW `WAIT_TIMEOUT_MS`** — it shipped inverted
  (300 s vs 180 s), so a fresh waiter ran out its whole budget while the lock was
  still younger than the stale threshold and threw `timed out waiting for the
  build lock`: a killed worker wedged the next build, the exact opposite of the
  documented guarantee. **(b) the break and the release are OWNERSHIP-CHECKED** —
  an unowned break lets a waiter free a merely-slow holder's lock, start a second
  build, and then have the original's `finally` delete the NEW holder's lock. The
  lock dir now carries an `owner` token; `release` refuses to remove a lock that
  is not ours, and the break re-reads the owner before acting.

## E2E local webServer: decap readiness + :4000 crash resilience

`e2e/playwright.config.js`'s local lane (`TARGET=local`) starts two webServers;
both are lint-locked by `e2e/webserver-readiness.test.js` (AST, not regex).

- **decap-server (:8081) waits on `port: 8081` (TCP), NOT a `url:` probe.** A
  `url: "http://localhost:8081/"` probe can never go ready — decap-server
  returns 404 for every GET route (/, /api/v1, /health) and Playwright's
  webServer readiness only accepts HTTP 200-403, so the whole local lane times
  out at the 60s webServer budget. (An earlier note here claimed the opposite;
  the `url:` form was tried and reverted — TCP is the only mechanism that works.)
- **The :4000 static server is `e2e/static-serve.js`, NOT bare `serve` (#1815).**
  Bare `serve@14`/`serve-handler` pipes the file ReadStream to the response with
  no `'error'` listener, so a racy post-open ENOENT (a TOCTOU on a `_site/admin/*`
  gem asset under the write-heavy admin lane) emits an UNHANDLED `'error'`,
  crashes the single shared :4000 process, and ERR_CONNECTION_REFUSED-es every
  later `@admin` spec — an 85-failure cascade that fails the canary cms/* PR's
  required `e2e / e2e`, blocks auto-merge, and wedges the prod loops. `static-
  serve.js` uses the SAME engine (serve-handler) + serve@14 config but overrides
  `createReadStream` to attach an `'error'` listener (so a post-open read error
  is handled, not fatal) plus an `uncaughtException` backstop. Never reintroduce
  bare `serve … -l 4000`.

## A cancelled required check blocks the merge (#1815)

If a canary cms/* PR shows every required check green + auto-merge armed yet sits
`mergeStateStatus: BLOCKED` and never lands — and an explicit
`gh api -X PUT repos/<r>/pulls/<n>/merge` returns
`405: Required status check "<ctx>" is cancelled` — the cause is a **cancelled
check-run for a required context shadowing the success on the same head sha**. No
merge mechanism (native auto-merge, explicit `pulls.merge`, or the nudge) can
override a cancelled required check, and GitHub picks **non-deterministically**
between a cancelled and a success run for the same context+sha (so the loop is
flaky, not consistently broken).

The source on these repos is a job with a `concurrency` group that fires
**multiple runs on the SAME head sha** — the canary loop flips labels
(`cms/draft`→`cms/ready`→`decap-cms/*`) without changing the sha, so an `on:
[opened, synchronize, labeled]` workflow fires a same-sha BURST of runs. The fix
is to give the required-check job **NO `concurrency` block at all** so every
same-sha run completes success. **Beware:** `cancel-in-progress: false` is NOT
enough — GitHub keeps the running run + only the LATEST pending run and CANCELS
the other pending dups in the group (documented behaviour), so a 4-run burst
still leaves ~2 cancelled (this defeated the first fix attempt at v0.1.27; the
real fix removed the concurrency entirely at v0.1.28). `cms-editorial-workflow.yml`'s
`validate-content` was the offender. **Rule:** any job that produces a REQUIRED
status context AND can be triggered more than once on the same sha
(label/multi-event triggers) must have NO `concurrency` group — a cancelled
required run is a hard, non-deterministic merge block. (Workflows triggered only
by `push`/`synchronize` — each a new sha — are safe to cancel; `secrets-scan` +
`visual-regression` keep `cancel-in-progress: true` for that reason.) Locked by
`workflow-graph.test.js`.

## Admin-bundle parity is bump-aware (#14)

`e2e/admin-bundle-parity.spec.js` byte-compares the SERVED admin bundle (prod +
the open PR's preview) against the local/source `theme/admin` tree. A **gem
bump** that changes the admin bundle (e.g. v0.1.x adds a `<script>` to
`theme/admin/index.html` — the #26 oauth-detector, confirmed on adamdaniel
#1913) makes PROD legitimately LAG: it keeps serving the OLD bundle until the
bump PR merges + deploys. A naive REQUIRED prod-vs-source check then fails
pre-merge (chicken-and-egg: prod can't match until the very PR that updates it
merges). The spec is therefore split into two gates:

- **REQUIRED (hard gate)** — the PR's OWN **preview** bundle byte-matches the
  local/source tree. Catches the real per-PR risk: a **broken preview build**
  (preview deployed bytes ≠ the PR). No bump excuse — it's the PR's own output.
- **PROD (bump-aware)** — compare prod's served bundle **VERSION** to the PR's
  source version. **Version marker = the served `index.html` manifest sha**:
  `index.html` lists every admin module as a `<script src>`, so any bundle
  add/remove/rename changes its bytes (and a `decap-cms@X.Y.Z` pin bump shows up
  too). If versions **DIFFER** (bump in progress, prod lags) → any prod-vs-source
  byte mismatch is **INFORMATIONAL** (logged `prod lags vX -> vY; reconciles on
  deploy`, not failed). If versions **MATCH** yet bytes differ → **REAL prod
  drift** (hand-edited prod / partial deploy at the same version) → **HARD
  FAIL** (preserves the original probe intent). When the marker is indeterminate
  (prod `index.html` 404/unreadable, or local missing) it fails SAFE to
  informational on the prod side; prod-drift at an unknown version is then caught
  by the scheduled `canary-prod` lane.

> **The walk EXCLUDES files the deploy never serves (#41, v0.1.14).** The
> version marker (`index.html` `<script>` manifest) is BLIND to non-script
> sidecar files. v0.1.13 added `collections.site.yml.example` (#5) + `README.md`
> to `theme/admin/` — SOURCE/DOC files the deploy COPY hook
> (`theme/lib/cms-platform-theme/decap_config_hook.rb`) and its deploy-time mirror
> (`scripts/render-decap-config.rb`) **explicitly SKIP** from `_site/admin`
> (`next if bn.end_with?('.base.yml') || skip.include?(bn)`). They 404 on prod
> AND preview, but the marker stayed byte-identical → the gate misread prod's
> legitimate 404 as same-version **drift** and red-failed every consumer bump.
> Fix: the walk filter is the testable `isExcludedAdminPath()` in
> `admin-bundle-parity.js`, mirroring the hook skip list (`*.base.yml`,
> `collections.site.yml[.example]`, `README.md`) on top of the per-deploy
> (`commit.json`) / preview-mutated (`config*.yml`) / dev-only
> (`index-{local,test}.html`) exclusions. A drift-guard test parses the Ruby
> `skip = […]` arrays so the JS predicate can never diverge from what the deploy
> actually serves. The same-version CONTENT-drift HARD FAIL is unchanged.

The decision logic is the pure, network-free `e2e/admin-bundle-parity.js`
(unit-tested by `e2e/admin-bundle-parity.test.js` with fixture bundles — the
spec only does the fetches). Outcome contract: on a gem-bump PR (prod older
version) parity PASSES via preview-vs-local; on a same-version prod byte-drift it
FAILS.

### The injected shells are identity-NORMALIZED before the byte compare (#17)

The parity byte-compare must NOT trip over the **per-environment `window.CMS_*`
injection** the render hook (and its deploy mirror) splices into the admin
shells. Three shells carry it — `admin/index.html` + `admin/reviews/index.html`
+ `admin/reviews/health.html` (the hook's `index*.html` + `reviews/*.html`
globs). The SERVED shell has an injected identity `<script>` block
(`window.CMS_REPO/CMS_SITE_ORIGIN/CMS_APEX/CMS_OAUTH_BASE_URL/CMS_SITE_TITLE`)
keyed to the *served* origin; the LOCAL source has **no such block at all** (it
only READS those globals at runtime). So a raw-byte compare of an injected shell
ALWAYS mismatched — the served block is present + per-env while source has none.
That false-failed the REQUIRED preview-vs-local gate (`PREVIEW BUNDLE != PR
SOURCE`) on **every** admin PR (regression from #14; confirmed adamdaniel #1913,
where the preview served valid complete pages and ONLY those 3 injected shells
mismatched).

The fix (`parityShaForFile` / `normalizeInjectedIdentity` in
`admin-bundle-parity.js`): an injected shell — classified by `isInjectedShell()`
mirroring the hook's globs **exactly** — is normalized in BOTH the served bytes
AND the local bytes before hashing: (1) the injected identity `<script>` block
(a `<script>` whose body is ONLY `window.CMS_<KEY>=…;` assignments) is STRIPPED
wholesale; (2) any inline `window.CMS_<KEY>=value` / `{{CMS_<KEY>}}` token is
collapsed to a per-key placeholder. The compare then runs on the MACHINERY (real
`<script src>` tags, structure) — preview-injected, prod-injected, and block-less
source all normalize-equal. A genuine machinery diff (added/removed/renamed
`<script src>`, structural edit) survives normalization and STILL hard-fails;
non-injected files (enhancer `.js`, CSS) are NEVER normalized (strict). The
injected key SET stays owned by `decap-config-render-parity.test.js` — the parity
probe deliberately does not assert on the block's internal composition. **If you
add another window.CMS_* identity shell, or change the hook's inject globs,
update `isInjectedShell()` in lockstep.**

## Self-CI lanes

`.github/workflows/self-ci.yml` is the machinery repo's own merge gate (every
other workflow here is an `on: workflow_call` reusable; `self-ci.yml` plus its
sibling `self-secrets-scan.yml` — which dogfoods the `secrets-scan.yml`
reusable on this repo's own history — are the only two that run directly on a
plain PR). It runs four FAST lanes on `pull_request` + `push` to `main`:

1. **actionlint** over `.github/workflows/*.yml` (downloads the pinned binary; hard-fail).
2. **ruby-theme-specs** — `theme/spec/*_test.rb` (hard-fail).
3. **node-unit-lints** — the pure-fs `e2e/*.test.js` lints, selected by an
   exclusion DENY list (build-/repo-dependent specs are denied; a new pure-fs
   lint is picked up automatically). Run with `TARGET=prod` +
   `PLAYWRIGHT_SKIP_BROWSER_DOWNLOAD=1` so no Jekyll/browser bring-up (hard-fail).
4. **cfn-lint** over the CloudFormation templates (advisory, `continue-on-error`).

`self-secrets-scan.yml` (#126) runs alongside it as its own workflow,
gitleaks-scanning the platform repo's diff on `pull_request`, incrementally on
`push` to `main`, and full-history weekly — the same posture the consumer
caller gets from `secrets-scan.yml`, applied to the machinery repo itself.

The heavy browser matrix + `@admin-write` write-path specs run in **CONSUMER**
e2e (dogfood / consuming-site CI), NOT in platform self-CI.

## Adding / porting a workflow

Make it `on: workflow_call` with site identity as `inputs`/`secrets`; keep
`github.repository`/`context.repo` (already portable). The site's `on:` trigger
+ `paths-ignore` + `run-name` live in a **thin caller** under
`examples/site/.github/workflows/`. If the workflow needs platform-owned scripts,
check the platform out into `.cms-platform/` (a dot-dir Jekyll ignores) at
`inputs.platform_ref` and run them from there (see `deploy-preview.yml`).

## Verify

```bash
ruby scripts/render-decap-config.rb <site> <site>/_site   # Decap render
node scaffold/create-site.js /tmp/x --yes --domain d --repo d --owner o   # scaffolder
# drift-guard + workflows: python3 -c 'import yaml,...' parse + bash -n the run: blocks
```

## Definition of done (non-trivial changes)

A merged PR with green unit-lints is **NOT** "done" for any non-trivial change
to this platform or a consumer. Green unit lints routinely ship a LIVE
regression (Decap UI drift, deploy-chain, dialog handling — e.g. the
double-`dialog.accept()` crash on loop run 27013147945 that NO unit lint or
adversarial code-review lens caught). "Done" additionally requires:

1. **Drive the prod-mutate validation loop to GREEN.** Dispatch
   `cms-publish-loop-prod.yml` (and `cms-media-roundtrip.yml` where the change
   can affect it) on the affected site and ITERATE until a run actually
   succeeds end-to-end (create → reflect → delete → 404) — not "the fix looks
   right" or "the dispatch-proof passed." The live loop is the real acceptance
   test for these CMS repos.
2. **Survey + drive every workflow green, in ALL THREE repos.** A platform
   change cascades, so the audit spans `cms-platform` AND **both** consumers
   (`adamdaniel.ai`, `jodidaniel.com`) — not just "the repo you edited". For
   EVERY workflow: it must have a run AFTER the last non-CI-generated push, and
   its most-recent run must SUCCEED. Iterate — re-dispatch stale / scheduled /
   manual ones — until that holds. ("CI-generated / non-real" = loop-canary
   churn + cleanup/auto-merge bot PRs + the automated `platform-bump` PR +
   auto-docs regen; those don't reset the bar — the reference point is the last
   *substantive* (human / code / content) change.)

   Survey method + nuances (2026-06-05 — `gh api repos/<r>/actions/workflows`
   → per-workflow latest run on `main`; compare its `head_sha`/`created_at` to
   HEAD / the last non-bot commit):
   - **In `cms-platform` itself, most workflows are `workflow_call`-only
     reusables** — they CANNOT run standalone (they show "no main run"); they're
     exercised when a consumer's thin caller invokes them, plus the harness
     lints run in **Self CI**. So the platform's own bar = **Self CI green on
     HEAD** (+ Cut release / Dependabot). Don't chase "no main run" on a reusable.
   - **A bump-skip-SKIPPED loop run is GREEN but is NOT a real validation.** The
     `recursion-gate` skips the prod loops on a bump-only push, so their
     post-bump run "succeeds" by skipping — that satisfies #2's "latest run
     succeeded" but NOT #1. Drive a REAL prod-mutate cycle by `workflow_dispatch`
     (it bypasses the bump-skip), confirming the heavy job actually ran.
   - **PR-triggered workflows** (`parity`, `preview-media`, `e2e`,
     `visual-regression`, the preview-env loops) last ran on the PR head, not
     `main` — a green run on the last real PR satisfies the bar; their
     "no main run" / stale-main-sha is expected.
   - **`startup_failure` or an old failed manual dispatch still counts as a RED
     latest run** — re-dispatch on current HEAD (the preview-env loops need a
     live `preview-pr<N>` target) until the latest run is green.
3. **No OPTIONAL / non-required check may fail either.** Drive `UNSTABLE` →
   clean, not just `BLOCKED` → mergeable. A merged PR with a red non-required
   check is not done — chase it to green, OR, if it is genuinely a
   user-credential / go-live blocker (jodidaniel `CMS_E2E_PAT`, the excluded
   jodidaniel #26), surface it explicitly rather than leaving it silently red.

This gate is part of the `platform-release-and-bump` flow — apply it after the
consumer bump, not before.

## E2E workflow matrix (ported)

The full e2e/Playwright matrix is ported. Two shapes:

- **Reusable + thin caller** (caller in `examples/site/.github/workflows/`):
  `e2e-tests`, `cms-publish-loop-preview`, `cms-delete-published-preview`,
  `cms-preview-loops` (workflow_dispatch); `canary-prod` (schedule + dispatch);
  `parity-preview`, `preview-media` (pull_request, always-run + early-skip — the
  reusable's selector/salient-detector IS the skip, so the caller has NO `paths:`
  to avoid the required-check missing-check trap). Each checks the platform out
  into `.cms-platform/` and references composites by `./.cms-platform/.github/actions/`.
- **Full workflow in `.github/workflows/`** (pinned to that shape by platform
  lints, run in the platform's dogfooding context, reference composites by local
  `./.github/actions/`): the three real-prod loops `cms-publish-loop-prod` /
  `cms-media-roundtrip` / `cms-publish-loop-host` (lint:
  `e2e/workflow-prod-loop-serialized.test.js` — shared `prod-mutating-loop`
  concurrency lane on each loop job, byte-identical [HARD mutual exclusion];
  `recursion-gate` job + `await-prod-deploy` gate; PLUS the three example
  callers' push triggers are PAIRWISE-DISJOINT — prod OWNS the shared infra
  paths (`admin/**`, `playwright.config.js`, `package*.json`, `_config.yml`,
  `_layouts/post.html`) on push, media/host cover them via their daily cron — so
  a single push can't fire two loops and co-arrival-evict one in the shared lane
  (#70). The shared concurrency group still serializes any cron/dispatch/push
  TIME-overlap by queuing; disjoint triggers remove the same-push co-arrival.)
  and `visual-regression` (lints:
  `e2e/visual-regression-content-skip.test.js` + `-skip-review.test.js` — the
  `paths:` content-skip list, the `visually-different` output, the conditional
  `regression-review` environment).

Composites ported: `.github/actions/await-prod-deploy` (commit-json-url now
derives from a `prod-url` input; no hardcoded site URL), `.github/actions/cms-recursion-gate`
(resolves `cms-recursion-churn.js` from the workspace or `.cms-platform/`).

**Deliberately NOT ported / simplified** (adamdaniel-only infra — see each
workflow's "PLATFORM PORT NOTES" header): the GHCR `ci-runner-image` prebaked
Jekyll/Ruby image + the `build-image` jobs + `container:` blocks (deps install
inline instead); the preview-loop `if: ${{ false }}` operational disable (an
adamdaniel dispatcher incident, not a platform invariant). (The stuck-PR
diagnostic and the newline auto-resolver ARE both shipped — see "Remaining
work" below: `scripts/diagnose-stuck-pr.js`, wired via
`e2e/with-stuck-pr-diagnostic.js`, and `scripts/auto-resolve-newline-conflict.js`;
also see the `cms-stuck-pr-triage` skill.) The prod-loop serialization lint was
updated to expect the two-job (no build-image) inline-deps shape while keeping
every load-bearing invariant. `visual-regression` still needs the consuming repo
to ship a buildable Jekyll site + Gemfile, AWS OIDC/S3/CloudFront, and a
`regression-review` Environment; baselines regenerate per-site.

### Prod-loop deploy-lane diagnostic — judge on the spec's OWN deploy (#21)

The prod-mutate / media-roundtrip loops watch the chain
**Decap → cms PR → auto-merge → deploy-production → URL reflects**. When the
URL never reflects, `e2e/deploy-pill.js#waitForChangeReflected` asks the
`makeDeployQueueExtender` callback (`e2e/github-actions-poll.js`) whether to keep
waiting (backlog draining) or give up (real miss).

**The DELETE leg (v0.1.17, #45):** the loops also DELETE the canary via the
editor and wait for `/blog/<slug>/` to 404. A "Delete published entry" commits
DIRECT to main via the git data API (`POST …/git/trees`), but the old call site
had no proof the dispatch fired, so a silent no-op surfaced 900s later as the
SAME "no deploy fired" symptom as a reflect miss. `confirmEditorDelete`
(`e2e/cms-editor-ui.js`) now arms + awaits that `POST /git/trees` as
dispatch-proof. Distinguish the two: a CREATE/reflect miss vs a DELETE no-op —
see the `browser-testing` skill ("Native window.confirm()" → dispatch proof).

**The #21 finding (triple-verified — trust it):** the 2099 e2e canary's OWN
`/blog/<slug>/` page **builds correctly** and is correctly excluded from public
aggregations — the `exclude_e2e_posts` theme plugin only stamps
`sitemap:false`/`feed_exclude:true`, it NEVER suppresses the page. So #21 ("URL
never reflects") is **NOT a theme/build defect** — do not touch
`exclude_e2e_posts`. The failure is in the deploy → serve → poll chain (S3 sync /
CloudFront / cache), and the **diagnostic itself mis-reported it**: the extender
judged the lane on a sliding ~5-min wall-clock window anchored to "now"
(`recentWindowMs`), so once the per-spec URL-reflect budget elapsed >5 min after
the spec's own deploy completed, the lane read "quiescent" and the extender
declared a REAL MISS ("deploy-production lane is QUIESCENT") even though the
deploy DID fire + complete — a **false negative**.

**The fix (shipped):** `deployLaneActivity` + `makeDeployQueueExtender` now anchor
on the create PR's `merged_at` (threaded from the specs via
`getMergedAt: () => getPullRequest(...).merged_at`, since the merge lands DURING
the reflect wait). They count `deploy-production` runs with
`run.created_at >= mergedAt`. A **completed** such run is CONCLUSIVE — the deploy
fired + finished, so the chain is healthy and the failure is **URL-not-served**;
the extender stops with `verdict.kind = 'deploy-completed-url-missing'`
(`realMiss:false`). **No** run `created_at>=mergedAt` + an idle lane is the
genuine miss (`verdict.kind = 'no-deploy-fired'`, `realMiss:true`). A prior
unrelated deploy (`created_at<mergedAt`) does NOT count. `deploy-pill.js` reads
`onBudgetExhausted.verdict` and self-reports the true leg: *"your deploy run DID
complete but the URL never served the marker (S3 sync / CloudFront / cache)"* vs
*"NO deploy-production run fired for your merge (trigger problem)"*. Without a
`mergedAt` the legacy wall-clock heuristic still drives the verdict (back-compat).
This makes the loop **self-diagnosing**; the actual URL-reflection fix is
downstream and needs a live run with the new output. Locked by
`e2e/github-actions-poll.test.js` (mergedAt-anchored cases) +
`e2e/deploy-pill.test.js` (the two self-reporting messages).

**The #1815 budget alignment (media-roundtrip):** the diagnosis above is only
trustworthy if the per-leg URL-REFLECT budget is WIDE enough to span the real
auto-merge latency BEFORE the extender's idle/give-up logic can fire. A live
media-roundtrip run failed at ~907s/15min reporting *"NO deploy-production run
fired"* while the canary auto-merge was simply SLOW — the merge hadn't landed
yet, so `getMergedAt` returned null (unanchored), the lane was legitimately
quiescent (nothing can deploy before the merge), and the extender mis-called it a
real miss. The prod-mutate twin failed the SAME way on its delete leg (run
26989348549). **The fix:** `cms-media-roundtrip.spec.js` raises each
`waitForChangeReflected` leg's `urlTimeoutMs` from 15 → **30 min**
(`REFLECT_TIMEOUT_MS`), matching its `waitForMerge` 30-min budget
(`MERGE_TIMEOUT_MS`), so the INITIAL reflect window alone spans the ~30-min
auto-merge latency; `TEST_TIMEOUT_MS` 100 → **130 min** and the
`cms-media-roundtrip.yml` job `timeout-minutes` 110 → **150** to fit. **Do NOT
shrink these back under the auto-merge latency** — `e2e/cms-loop-budget-alignment.test.js`
(a PLATFORM_META_SPEC pure-fs lint) locks: media's MIN reflect leg `>=`
prod-mutate's AND `>=` the 30-min floor, media's `waitForMerge` `>=` prod-mutate's,
media's `TEST_TIMEOUT_MS` `>=` prod-mutate's, and the spec timeout fits the job
`timeout-minutes`. The publish mechanism + canaries are unchanged — only budgets.

### Ephemeral canary branch hygiene (#22)

The prod loops force-push EPHEMERAL per-run branches that orphan when a cycle
cancels/fails (~35 piled up on adamdaniel): `cms/posts/2099-12-31-e2e-prod-mutate-<runId>`,
`cms/posts/2099-12-31-e2e-media-roundtrip-<runId>` (Decap, runId = `Date.now()`),
and the host loop's `cms/e2e/canary-*` + `cms/e2e-fixture/*`. Two defences:

- **Per-loop `if: always()` cleanup step** in each loop reusable
  (`cms-publish-loop-prod.yml`, `cms-media-roundtrip.yml`,
  `cms-publish-loop-host.yml`): runs on success/failure/cancel,
  `continue-on-error: true` + every delete `|| echo`-guarded (**FAIL-OPEN** — a
  cleanup hiccup never fails the loop). Since runId is `Date.now()`, it
  **pattern-deletes** every branch on the loop's OWN prefix that has **no open
  PR** (a live cycle's branch always carries its in-flight cms/* PR). Auth via
  `CMS_E2E_PAT` (the workflow grants only `contents:read`).
- **`sweep-stale-cms-prs.yml`** extends `TEST_ONLY_PATTERNS` with the two
  `cms/posts/2099-12-31-e2e-{prod-mutate,media-roundtrip}-` prefixes so the daily
  age-gated, no-open-PR, `[sweep-keep]`-opt-out Tier 1 close + Tier 3 branch prune
  now reaps those orphans too. Safe to safelist because the 2099 + `e2e-` loop
  signature is NEVER human-authored (unlike a bare `cms/posts/<slug>` draft).

Locked by `e2e/workflow-loop-branch-cleanup.test.js` (parses with the `yaml`
lib). If you add a new ephemeral loop branch prefix, add its cleanup step AND
extend that lint + the sweep safelist.

### A bump push fires ALL THREE loops, so the bump-skip must not be brittle

The `recursion-gate`'s bump-skip (#57) is what stops a platform-version bump from
re-firing the prod loops, and it is load-bearing for a reason #70's
disjoint-push-triggers fix cannot cover: **a bump rewrites the `uses:@<ref>` pin
in EVERY loop's own workflow file**, which is each loop's own trigger path — so a
bump always fires all three at once. They share the `prod-mutating-loop`
concurrency group, which holds an in-flight run but **drops a co-arriving
sibling**, so without the skip a bump costs you a CANCELLED loop.

Observed live on adamdaniel.ai (2026-08-07): the gate required EVERY changed path
to be a version pin, and a single `AGENTS.md` commit landed on the bump PR — the
natural place for a doc correction that goes with the bump — was enough to fail
that test. All three loops fired; `media-roundtrip`'s heavy job was cancelled
outright (run 31185014802) while `host-loop`'s survived. So `isBumpOnlyPush` now
also tolerates paths that **cannot change the built site** (`AGENTS.md`,
`CLAUDE.md`, `README.md`, `LICENSE`, `docs/**` — exactly what the deploy
workflows already `paths-ignore`). A bump carrying real content, a script, a
config, or CSS still fails it and correctly RUNS. Both directions are locked by
`e2e/cms-recursion-churn.test.js`.

## Remaining work

Ported as reusable `workflow_call` + thin callers: deploy (prod+preview),
`cms-editorial-workflow`, `secrets-scan`, `publish-scheduled-posts`,
`sweep-stale-cms-prs`, the full **e2e matrix** (`e2e-tests` + the 10
loop/visual/parity/media workflows + the `await-prod-deploy` /
`cms-recursion-gate` / `post-failure-comment` composites + the `e2e/` harness),
and the **hygiene long-tail**: `auto-resolve-newline-conflict` (+ its
`scripts/auto-resolve-newline-conflict.js`), `cleanup-stale-fixture-branches`,
`dependabot-auto-merge`, `dependabot-comment-sync` (+ its
`scripts/sync-action-pin-comments.sh`; the adamdaniel-only PAT secret was
generalised to the `workflow_sha_comment_pat` input, and the executed script is
now platform-pinned via `.cms-platform/` rather than the PR-head copy — strictly
tighter than the original `pull_request_target` posture), and
`label-non-decap-prs` (keys its Decap-branch prefix off the platform
`e2e/cms-fixture-pr.js` `FIXTURE_BRANCH_PREFIX`).

Both **e2e meta-lints** are now fixed: `visual-regression-content-skip.test.js`
reads `admin/config.base.yml` (the platform's Decap config; `config.yml` is
render-only) and `playwright-image-drift.test.js` loads against the now-ported
`scripts/check-playwright-image-drift.js`. The workflow-structure lints were
already adjusted for the reusable shape (`workflow-run-name` / `dependabot-skip`
exempt `workflow_call`-only reusables). Dropped adamdaniel-only CI (GHCR
`ci-runner-image`, `select-specs` sharding, the finalize merge-gate) is intentional.

**Completeness pass (PR #1 refresh, 2026-05-29).** Ported the `adamdaniel.ai@main`
fix clusters that postdated the initial extraction: `#1810` e2e/test-fixture
exclusion from public aggregation (theme `exclude_e2e_posts` plugin + `feed_exclude`
filtering in `auto_tag_pages` / `tag_feeds` / `atom_feed.xml` / `tag.html`),
`#1840`+`#1809` slug consolidation + the shared `e2e/public-content.js` crawl-set
(+ `slugify-parity` / `preview-deploy-superset` / `e2e-posts-public-exclusion`
tests), `#1844` probe ⊆ deploy (`select-specs.affectsDeployedPreview`),
`#1824`/`#1830`/`#1845` prod-loop + media-roundtrip robustness, and `#1825`
**`cms-automerge-nudge`** — now a reusable `workflow_call` (site supplies its
required-check contexts as an input) + thin caller + lint; treat it like the other
reusables for the run-name/dispatch lint exemption. Also shipped the missing
`scripts/scrub-secrets.js` (the failure reporter referenced a path the platform
didn't ship — un-scrubbed PR output was a secret-leak), local pre-commit hygiene
(`.githooks/pre-commit`, `scripts/secrets-scan.sh` + `lint-staged.sh`, `.gitleaks.toml`
as the single allowlist shared with `secrets-scan.yml`), and `e2e/package-lock.json`.
Stale identity-bound tests were re-parameterized to the env/`window.CMS_*` model.

**`e2e-required-stub.yml` — the required-check-stub IS ported (reusable).**
A docs-/infra-only PR is `paths-ignore`d out of `e2e-tests.yml`, so the
REQUIRED `e2e / e2e` status check would otherwise never report and branch
protection blocks the PR forever (the "missing-check trap"). The platform
ships `.github/workflows/e2e-required-stub.yml` (a generic one-context
`e2e / e2e` synthetic-pass stub), an example caller
(`examples/site/.github/workflows/e2e-stub.yml`), and a lint
(`e2e/required-check-stub-paths.test.js`) that enforces the caller's
`paths:` mirrors `e2e-tests.yml`'s `paths-ignore` in lockstep. This replaces
the old per-shard `required-check-stubs.yml` that #1858 removed.

Still open:
- **Deliberate skips — NOT ported** (each is repo-/site-specific machinery, not a
  reusable; a consuming site authors its own):
  - `code-quality` — platform-self-CI (lints the machinery itself); kept
    **platform-internal and NOT shipped to consumers**. The self-test fixtures
    (`e2e/fixture-site`, `e2e/fixture-site-singlepage`) let
    `cd e2e && npm ci && npx playwright test` run the harness standalone, so the
    build-dependent e2e specs go green in self-CI (not only a consuming site).
  - `ci-runner-image` — adamdaniel-only GHCR image; already dropped in the e2e
    port (inline deps used instead).
- **`playwright-image-drift` real-repo subtest caveat**: the guard's
  "real repo is drift-free" subtest reads a root `package-lock.json` +
  `.github/ci-runner/Dockerfile`, neither of which the machinery repo ships
  (no installable lockfile here); it exercises fully against the synthetic
  `scaffold()` fixtures and runs green in a consuming site that has both.
- **Pixel-level visual-regression baselines were retired in v0.1.34** (see
  "#86 retire the dead committed-PNG visual suite" below) — replaced by
  structural "renders" smoke checks + a prod-diffing VIDEO pipeline
  (`visual-regression.yml` + `compute-visual-diffs.js`) that needs no
  committed baselines at all. The only committed snapshots a new site might
  need to regenerate are the ARIA-contract YAML snapshots under
  `e2e/cms-editor-aria-contract.spec.js-snapshots/*.aria.yml`
  (`npx playwright test --update-snapshots` still applies to those
  specifically, not to pixel screenshots).

## Version history (v0.1.0 → v0.1.72)

All are tagged GitHub releases (release via `gh workflow run release.yml -f version=vX.Y.Z`).

- **v0.1.0** — initial extraction; dogfooded on adamdaniel.ai (prod green, pixel-identical).
- **v0.1.1** — org-portability hardening (de-identified secrets-scan / identity).
- **v0.1.2** — fixes pass.
- **v0.1.3** — interim.
- **v0.1.4** — **admin consolidation (Option 1A, issue #5 GOAL 1):** `admin/`
  relocated to `theme/admin/` so the gem ships it; the render hook copies the
  gem-resident machinery into `_site/admin` + renders `config.yml`; consumers
  delete their vendored `admin/` and keep only the seam; drift-guard becomes
  skills-only. (See "Admin delivery".)
- **v0.1.5** — **consumer-context spec rule:** specs that run in CONSUMER mode
  must read the SERVED admin bytes, not `theme/admin`. Fixed `preview-bridge.spec.js`;
  added `e2e/admin-spec-source-read-lint.test.js`.
- **v0.1.6** — **editorial-label audit:** dialog regression guard +
  `audit-editorial-labels.js` + reusable `editorial-label-audit.yml`.
- **v0.1.7** — **base_collections opt-out** (`cms.base_collections` keep-list;
  `theme/spec/base_collections_filter_test.rb`).
- **v0.1.8** — **e2e flake fix:** decap-server `webServer` waits on the open TCP
  `port: 8081`, not a `url:` HTTP probe (decap 404s every GET route, which
  Playwright's readiness rejects — the `url:` form timed out the whole local
  lane). See "E2E local webServer".
- **v0.1.9–v0.1.12** — **issue sweep** (2026-06-04): #25 neutral gem logo, #23
  scaffold seeds `preview.md` + `404.html`, #26 OAuth-restriction admin banner,
  #29 single-version pin-consistency guard (`scripts/check-platform-pin-consistency.js`),
  #21 self-diagnosing deploy-lane diagnostic, #22 ephemeral canary-branch
  cleanup, #5 GOAL 2 `field_library` + `$ref`, #33 base_collections single-page
  e2e skips; plus #14 bump-aware admin parity + #17 injected-shell identity
  normalization + #16 PLATFORM_META_SPECS recurrence guard. Both consumers
  reconciled to single-version lockstep.
- **v0.1.13** (2026-06-05) — **#39 CloudFront `ErrorCachingMinTTL 300→0`** in the
  bootstrap template (root cause of the #21/#1815 canary-URL non-reflection:
  CloudFront negative-cached the pre-create 404) + `deploy.sh`
  `CreateApexDnsRecords` env passthrough; **#40** broader single-page e2e skips
  (reviews/preview-shell/draft-isolation/canary-prod) + media-roundtrip budget
  alignment.
- **v0.1.14** (2026-06-05) — **#41 admin-parity walk excludes deploy-skipped
  source/doc files** (`isExcludedAdminPath()` mirrors the copy-hook skip list +
  a Ruby-skip-list drift guard); fixes false same-version "drift" on
  `README.md`/`collections.site.yml.example` during a bump.
- **v0.1.15** (2026-06-05) — **#42 parity-preview exports `SITE_ROOT`** so a
  single-page consumer's `@parity` crawl reads the CONSUMER `_config.yml`
  (base_collections opt-out) instead of the platform fixture — stops the lane
  crawling `/blog//tags` on jodidaniel.com.
- **v0.1.16** (2026-06-05) — **#44 editorial-label-audit passes `--repo`** so the
  daily audit stops failing `fatal: not a git repository` (the reusable
  sparse-checks-out only the script, so `gh pr list` had no repo context;
  script also falls back to `GITHUB_REPOSITORY`).
- **v0.1.17** (2026-06-05) — **#45 delete-leg dispatch proof**: the prod-mutate /
  media loops' `confirmEditorDelete` now arms `waitForRequest(POST …/git/trees)`
  BEFORE the editor Delete click and awaits it, so a silent delete no-op throws
  at the real fault site instead of timing out 900s later in the URL-404 wait
  (#1815 delete-phase). See the `browser-testing` skill.
- **v0.1.18** (2026-06-05) — **#47 delete helper must not register a 2nd dialog
  handler** (the double-`dialog.accept()` regression invisible to unit lints);
  + the "Definition of done" section captured here.
- **v0.1.19** (2026-06-05) — **#48 recover a Decap published-delete into an
  auto-merged PR on protected `main`** (the `admin/publish-via-auto-merge.js`
  shim path; #1815 delete-phase).
- **v0.1.20** (2026-06-05) — **workflow-SET parity + PAT consolidation epic**:
  #54 pin-consistency now asserts the consumer's `.github/workflows/` basename
  set == the platform-dictated canonical set; #53 comment-sync PAT consolidated
  onto `CMS_PLATFORM_PAT` (fine-grained only); #52 repo-variable setter
  centralization; the contributor manual eliminated.
- **v0.1.21** (2026-06-05) — **#57 recursion-gate skips the prod-mutating loops
  on a platform-version-bump push** (the bump touches the loop's own workflow
  file, which would otherwise re-fire it and race the bump deploy); + #55
  doc-fix sweep, #56 prod/preview host-loop guards for `base_collections:[]`.
- **v0.1.22** (2026-06-05) — **#58 export `SITE_ROOT` on EVERY `.cms-platform/e2e`
  harness invocation** (5 loop reusables + canary-prod + delete-preview +
  preview-media + visual-regression + e2e-tests), enforced by
  `e2e/loop-site-root-lint.test.js` (#1815 host-loop gap).
- **v0.1.23** (2026-06-05) — **#59 (#13) `platform-bump.yml` is atomic** (bumps
  every pinned ref in one pin-consistent PR + checks out with the caller PAT for
  workflow-file push auth); + #60 the MAIN host-loop `test()` guard + a
  per-test-block guard-registry lint.
- **v0.1.24** (2026-06-05) — **#61 full regex→AST rewrite of the guard-registry
  detectors** (`e2e/spec-ast.js`, acorn 8.16.0 + acorn-walk 8.3.5, exact-pinned
  past the 7-day cooling-off). "AST always, never regex for code structure."
- **v0.1.25** (2026-06-05) — **#63 pin-consistency catches thin-caller CONTENT
  drift**, not just version refs (a consumer caller whose body diverged from the
  platform template at the pinned ref).
- **v0.1.26** (2026-06-06) — **#64 crash-resilient :4000 webServer + recover
  stuck-green canaries** (#1815). `e2e/static-serve.js` replaces bare `serve`
  (which crashed the shared :4000 process on a racy ReadStream ENOENT, an
  85-failure `@admin` cascade); `cms-automerge-nudge.yml` now recovers
  UNKNOWN-state stuck-green canaries via a fresh-re-queried, stub-safe explicit
  `pulls.merge`. See "E2E local webServer".
- **v0.1.27** (2026-06-06) — **#66 `validate-content` cancel-in-progress:false**
  (#1815). The editorial workflow fired several runs on the same canary head sha
  (an opened+synchronize+labeled burst), and a cancelled `validate-content`
  check-run shadowed the success → GitHub blocked the merge non-deterministically
  (live 405). This set cancel-in-progress:false — but that was an INCOMPLETE fix
  (see v0.1.28). Nudge `headIsTrulyGreen` also made cancelled-aware. See "A
  cancelled required check blocks the merge".
- **v0.1.28** (2026-06-06) — **#68 remove `validate-content`'s `concurrency`
  block entirely** (#1815, the REAL fix). `cancel-in-progress:false` (v0.1.27)
  was not enough: GitHub keeps the running + latest-pending run and CANCELS the
  other pending dups in a same-sha burst, so cancelled check-runs persisted and
  the loops still merged only via the success-wins coin-flip (#1990/#1993 merged
  with 2 cancelled + 2 success; #1996 blocked with the same). With NO concurrency
  every same-sha run completes success → no cancelled shadow → deterministic
  merge. Lint updated to assert no concurrency block.
- **v0.1.29** (2026-06-06) — **loop reliability + OAuth delivery + a spec migration**:
  - **#70 co-arrival eviction → disjoint push triggers (#73).** Keep the shared
    `prod-mutating-loop` group (HARD mutual exclusion) but make the three loops'
    PUSH triggers PAIRWISE-DISJOINT — prod OWNS the shared infra paths on push,
    media/host cover them via their daily cron — so a single push can't fire two
    loops and co-arrival-evict one. (Superseded an initial run-id lane-gate that
    an adversarial review showed downgraded hard exclusion to fail-open
    best-effort — re-run queue-jumping + media's 150min run >> a 45min gate
    timeout.) New lint asserts disjoint push paths + prod-owns-infra.
  - **#1815 host leg — byte-lock tolerates one in-flight marker (#73).** The host
    publish-loop's create PR appends an `e2e-publish-loop:` marker to the
    persistent `_e2e/canary-post.md`; the strict byte-lock had rejected the
    loop's OWN PR (its heavy job had been red 40+ runs — only the ephemeral-post
    prod/media loops were ever green). `stripInFlightMarker` (self-contained; ONE
    marker pattern shared across the byte-lock, the spec afterAll, and
    reset-orphaned-canary.sh; LF-enforced via .gitattributes) tolerates exactly
    one marker while real drift + the multi-marker orphan (#1861) still fail loud.
  - **#69 deliver OAuth-proxy + bootstrap as delegating wrappers (#72).** The
    scaffolder emits committed thin `oauth-proxy/deploy.sh` +
    `infrastructure/bootstrap/deploy.sh` that read platform.lock, check the
    platform out at `platform_ref`, and `exec` the platform's real deploy.sh
    (default OAuth scope `repo,user,workflow`) — consumers vendor no
    `lambda.py`/`template.yaml`/bootstrap template. A scope-widening redeploy
    needs a MANUAL OAuth-App re-consent. Locked by scaffold-deploy-delegators.test.js.
  - **adamdaniel#2007-P3 — migrate `normalize_empty_slug_test.rb` to the gem
    theme/spec (#74)** (the consumer test required a now-absent `_plugins/` path).
- **v0.1.30** (2026-06-06) — **#76 kill the admin link-crawler TOCTOU flake
  (#1815).** `_site/admin/*` are gem assets copied by the `:post_write` render
  hook, NOT generated by Jekyll, so Jekyll's `cleanup` phase deleted them at the
  start of every build (incl. the in-test `jekyll build`s @admin-write specs run
  against the live `_site`); the @admin-read link-crawler HEADed into the
  delete→recopy window → a ~6% transient 404 that intermittently red-ed
  canary-PR e2e and the loops. Fix: `keep_files: [admin]` (fixture + scaffolder)
  so cleanup never deletes `_site/admin`, + atomic gem-asset copy (temp+rename)
  in both parity-locked render paths. Locked by `e2e/admin-keep-files.test.js`.
  Consumers add `keep_files: [admin]` to `_config.yml` on bump.
- **v0.1.31** (2026-06-06) — **#78 host-loop SITE_ROOT read fix (#1815 host
  leg, next layer).** The v0.1.29 byte-lock fix let the host loop get PAST its
  create leg, exposing the next layer: `cms-unpublish-republish.spec.js` read
  its `_posts/` canary via `path.join(__dirname, "..", FIXTURE_PATH)` = the
  `.cms-platform/` harness checkout on a consumer → ENOENT → the host loop died
  on spec #4 (live run 27069585769). Both reads now use `SITE_ROOT` (the #1815
  v0.1.22 universal rule, applied to these two content reads the workflow-level
  lint couldn't see). New AST lint `e2e/spec-site-root-reads.test.js` flags any
  @lane:real spec reading SITE content (_posts/_e2e/_tags/_drafts/assets) via
  the platform checkout (platform SOURCE reads like theme/admin are allowed).
- **v0.1.32** (2026-06-06) — **#81 host-loop layer #4 (#1815 host leg, tracked in
  #80).** `cms-unpublish-republish.spec.js` reset its canary via a DIRECT PUT to
  `main` (`writeFixtureOnMain`) — which 409s on a consumer whose `main` ruleset
  has `bypass_actors:[]` ("Changes must be made through a pull request"). A failed
  run therefore couldn't restore baseline and left the canary `published:true`,
  SERVING the test fixture publicly at `/blog/e2e-unpublish-canary/`. Switched to
  `seedFixtureViaPr` (a `cms/ready`-labelled auto-merge PR, fire-and-forget) —
  the same path `cms-publish-loop.spec.js`'s afterAll already uses (its helper's
  comment literally explains a direct PUT 409s). The host loop now passes specs
  1–3 live (byte-lock v0.1.29 + keep_files v0.1.30 + SITE_ROOT v0.1.31); the
  remaining spec-#4 failure (a `locator.click` timeout in the unpublish Save/
  Publish leg) is tracked in #80 ("keep peeling to 4/4").
- **v0.1.33** (2026-06-25) — **#96 host-loop layer #5 (#1815 host leg, #80).**
  The v0.1.32 host-loop verification run passed specs 1-3 live but spec #4
  (`cms-unpublish-republish`) still failed: the *second* (unpublish) `saveEntry`
  timed out clicking Save, which the on-prod log resolved to a `<button
  disabled ...SaveButton...>` — the form was never dirtied. After the re-publish
  leg's "Publish now" merges the editorial-workflow PR, Decap reloads the entry
  in place and the Published switch transiently reads its default (OFF) before
  re-hydrating the persisted `published: true`; the idempotent
  `setPublished(false)` raced into that window, saw OFF, skipped the click, and
  left Save disabled. Fix: a symmetric pre-toggle gate (mirroring the step-1
  "reads OFF (baseline)" wait) that re-opens the entry fresh and waits for the
  switch to read ON before toggling OFF, plus an `ENTRY_EDIT_URL` SSOT for the
  canary edit hash-route. Real-prod 4/4 confirmation = a host-loop re-dispatch
  after the consumer bumps land.
- **v0.1.34** (2026-06-25) — **#86 retire the dead committed-PNG visual suite.**
  `e2e/visual-regression.spec.js`'s `toHaveScreenshot` tests had no baselines
  (all 32 committed PNGs were deleted 2026-05-06 and never regenerated), so the
  suite only stayed green by skipping — until the first curated prod tag
  ("quotes", adamdaniel #2057) un-skipped the tag tests and hard-failed
  "snapshot doesn't exist", blocking a content PR. Replaced the 4 pixel tests
  with structural "renders" smoke checks (non-error status + visible heading)
  that KEEP the original content-discovery skip-guards (so they still skip on a
  `base_collections:[]` bio — the #33 contract) and run on a full site; deleted
  `e2e/visual-change-guard.spec.js` (it only bounded the now-gone PNGs) + its 5
  refs. Pixel visual-regression is owned by the prod-diffing video pipeline
  (`visual-regression.yml` + `compute-visual-diffs.js`), which machine-classifies
  PR-vs-production diffs and gates merges via the required `regression-review`
  environment; the structural checks are net-additive (all public projects,
  content-only PRs). Adversarially reviewed (4 lenses): 0 confirmed blockers.
- **v0.1.35** (2026-06-25) — **#100 reaper chokes on Decap smart-quote branch
  names.** `regression-review-reaper.yml` interpolated the PR head branch
  straight into the runs-list URL (`?branch=${HEAD_REF}`). A Decap content-PR
  branch carries the post title verbatim (spaces + smart-quotes), so
  adamdaniel #2057 (`…safety-“somewhat-less-robust”`) produced an UN-encoded
  URL → GitHub returned an HTML error page → `--jq` failed ("invalid character
  '<'") → the job went red under `set -euo pipefail` on every branch sync.
  Fix: build the query with `gh api -X GET -f branch=… -f status=… -f
  per_page=…` (URL-encodes the fields; `-X GET` is required because gh defaults
  to POST once any `-f` is present), and fail OPEN (`|| true`) on the runs-list
  + pending-deployments lookups. Verified live against #2057's exact branch:
  old call → "invalid character '<'", new call → clean total_count.
- **v0.1.36** (2026-06-26) — **#80 host-loop layers 6 & 7 — `saveEntry` vs the
  editorial auto-save.** The v0.1.33 layer-5 fix worked (the unpublish toggle
  now flips ON→OFF), exposing layer 6: after the re-publish leg's Publish-Now
  the entry is in the editorial `Status: Ready` state, where toggling Published
  AUTO-PERSISTS into the open PR — Save goes `disabled` and the transient
  "Changes saved" toast fires/fades in the toggle step. The old `Save.click()`
  30s-timed-out on the disabled button → publishViaUi never ran → unpublish
  never merged. An adversarial review caught layer 7 pre-flight: tolerating the
  disabled Save but still gating on the toast would ALSO fail (toast already
  faded). Fix: `saveEntry` clicks Save only while actionable (4s window) and
  confirms the write via EITHER the toast OR the PERSISTENT saved state (Save
  `disabled` == no unsaved changes). Safe across all 5 callers (each makes a
  guaranteed-real edit; consecutive saves are page.goto-separated → no
  false-pass). Diagnosed from the downloaded test-failed screenshot.
- **v0.1.37** (2026-06-26) — **#85 / #80 layer 8 — Publish-Now 405 dead-end.**
  Multi-agent investigation root-caused the "Publish-Now silently doesn't take
  effect" defect (#85) = the host-loop unpublish leg's "chain never fired": an
  editorial PR auto-merges only on a fresh `decap-cms/pending_publish`/`cms/ready`
  `labeled` event. On an unpublish/re-edit, Decap's "Publish Now" `PUT /merge`
  returns **405** "not mergeable" (checks not recomputed; base just moved), but
  the admin shim `theme/admin/publish-via-auto-merge.js` only recovered on **422**
  "rule violations" → the 405 dead-ended (no `cms/ready`, no auto-merge, no
  deploy). A fresh post works because it opens as a Draft (the Draft→Ready click
  arms auto-merge regardless of the 405). Fix: broaden the **merge** matcher to
  recover on 405/409 too (arm `cms/ready` — correct/idempotent; PR merges via
  auto-merge-when-ready once checks pass); **delete-ref** stays on 422; +3 unit
  tests + a `console.info` to confirm the recovery on the next run. Since the
  host-loop test drives the REAL prod `/admin` shim, this fixes #85 for editors
  AND host-loop spec-4. Evidence: run 28211841171 trace `PUT /pulls/2283/merge
  → 405`, zero `cms/ready` POSTs, deploy queue empty.
- **v0.1.38** (2026-06-28) — **#80 host-loop layer 9 + #85 — the armed PR was
  CLOSED before auto-merge could run.** The v0.1.37 arm-on-405 fix worked (live
  run 28240375064: `PUT /pulls/2295/merge → 405` then `POST /issues/2295/labels`
  arming `cms/ready`), but the freshly-armed, MERGEABLE editorial PR was CLOSED
  ~2s later, before `auto-merge-when-ready` ran, so `enablePullRequestAutoMerge`
  errored "Pull request is closed" → never merged, never deployed. Root cause
  (multi-agent audit + adversarial verification of the Decap 3.12.2 source): the
  shim handed Decap a **synthetic HTTP 200 `{merged:true}`** on its 405/422
  recovery. Decap's `publishUnpublishedEntry` is `await mergePR(pr); await
  deleteBranch(branch)` — `deleteBranch` is UNCONDITIONAL and the merge body's
  `merged` flag is DISCARDED, so any 2xx makes Decap DELETE the editorial head
  ref, which auto-closes the still-open, unmerged PR (PR #2295 timeline:
  `head_ref_deleted` + `closed`, mergedAt:null, by the Decap OAuth user — NOT a
  workflow). Fix (theme/admin/publish-via-auto-merge.js): the **merge** matcher
  still arms `cms/ready` but now returns a **synthetic 422** (deliberately NOT a
  2xx, and NOT 405 — Decap routes exactly 405 to `forceMergePR`, a direct
  default-branch commit), so Decap's `mergePR` re-throws and SKIPS `deleteBranch`
  → the PR stays open + armed → auto-merge-when-ready lands it when the checks
  pass. The **delete-ref** matcher keeps its synthetic `merged:true` (its branch
  is shim-created, not Decap-managed). Also: `console.info`→`console.warn` (the
  host-loop trace only captures error/warn); and `cms-editorial-workflow.yml`'s
  `auto-merge-when-ready` now falls back to a conditional direct squash
  `pulls.merge` when `enablePullRequestAutoMerge` reports "clean status" (every
  required check already green → nothing to enqueue → it would otherwise throw),
  swallowing already-merged/closed idempotently (branch protection still
  enforces the checks at merge time). Updated the shim unit + browser specs and
  added a `clean-status` fallback regression lint.
- **v0.1.39** (2026-06-28) — **#80 host-loop layer 10 — editorial-limbo delete
  leg.** The v0.1.38 422 shim fixed layer 9 (live-verified: editorial PR #2309
  stayed open + armed + auto-merged), but the 422 makes Decap's "Publish Now"
  report an error, so Decap leaves the entry in editorial `Status: Ready` limbo
  (UNPUBLISHED_ENTRY_PUBLISH_FAILURE keeps the entity; the editor shows "Delete
  **un**published entry"). The host-loop delete specs hand-rolled a "Delete
  published entry" click that 30s-timed-out on the wrong affordance
  (cms-delete-published.spec.js:368; run 28340095169). Fix: bring the delete
  specs up to the **proven-green** `cms-publish-loop-prod-mutate.spec.js`
  pattern — after Publish-Now, capture the create PR + `waitForMerge`, then
  `reopenForPublishedDelete` (poll-reloads until Decap drops the now-merged
  editorial entry and shows the PUBLISHED file — a full reload is required;
  Decap's PR-based editorial list only re-derives on CONFIG_SUCCESS), then
  `confirmEditorDelete(() => clickEditorDelete())` (arms a POST /git/trees
  watcher as positive proof the delete dispatched), then label the recovered
  delete PR `cms/ready`. Applied to `cms-delete-published.spec.js` +
  `cms-tags-lifecycle.spec.js` (titleName `/^Name$/i`; canaryMarker = the runId,
  which lands in the file CONTENT — the hyphenated slug is only the filename);
  `cms-publish-loop.spec.js` cleanup leg now uses the limbo-tolerant
  `saveEntry`+`publishViaUi` helpers. `cms-publish-loop-host.yml`
  `timeout-minutes` 105→150 (the delete legs now waitForMerge+reopen). Shim and
  `cms-unpublish-republish.spec.js` unchanged. Decided via multi-agent audit of
  the Decap 3.12.2 editorial-state lifecycle (Option A kept; Option B — 2xx +
  no-op Decap's branch-delete — rejected: re-introduces layer 9 and the no-op is
  indistinguishable from a legit discard).

- **v0.1.40** (2026-06-29) — **#80 host-loop layer 11 — unpublish leg's stale
  editorial draft + reused branch.** v0.1.39 took the loop to 3/4 (both delete
  specs green); cms-unpublish-republish still failed at the UNPUBLISH leg's
  URL-404 wait ("chain never fired", run 28342322662). Root cause: the spec
  reuses a FIXED slug (`2024-01-02-e2e-unpublish-canary`), and (a) the re-open
  step did a hash-route `goto` WITHOUT a full reload, so Decap re-read its
  in-memory editorial draft from the re-publish leg's 422 (Decap re-derives
  editorial state only on a fresh boot / CONFIG_SUCCESS) — the screenshot showed
  Status:Ready + "Not yet published" with Published OFF; and (b) the re-publish
  leg's merged `cms/posts/<slug>` branch LINGERED (`delete_branch_on_merge=false`
  on the consumers), so even a fresh edit couldn't open a new editorial PR
  (createBranch 422s on the existing ref). Fix: (1) the unpublish re-open now does
  an explicit `page.reload()` so Decap re-fetches the entry as the now-published
  file; (2) **enabled `delete_branch_on_merge=true` on both consumers** so a
  merged editorial branch is removed and the next leg/edit opens a fresh PR.
  NOTE: the consumers had drifted to `delete_branch_on_merge=false` (no recorded
  reason; possibly an old fix) — the platform was DESIGNED for it ON
  (cleanup-stale-fixture-branches header). Re-enabled per owner direction with a
  regression watch; revert to false + an in-spec branch-delete is the fallback if
  it regresses elsewhere. cms-delete-published / cms-tags-lifecycle / cms-publish-loop
  unchanged from v0.1.39; the 3-of-4 that passed at `delete_branch_on_merge=false`
  must be re-confirmed green at `true`.

- **v0.1.41** (2026-06-29) — **#80 host-loop layer 11b — unpublish Save no-op on a
  deep-route-reloaded entry.** v0.1.40 (layer 11a) took the loop to 3/4 but
  cms-unpublish-republish leg-2 still failed: a bare `goto(ENTRY_EDIT_URL)+page.reload()`
  on the deep hash route re-derived the post-422 editorial-limbo draft (run
  28372038163 showed status "Published" + "UNSAVED CHANGES" but the toggle-OFF
  Save NO-OP'd — no toast, no branch, no PR, "UNSAVED CHANGES" persisted). Root
  cause (Decap 3.12.2 source audit): the Editor's Save → `actions/entries.ts
  persistEntry`; if `fieldsErrors` is non-empty at click time it `return
  Promise.reject()` with NO toast (only a presence-error shows one), and a bare
  deep-route reload re-boots the app so the toggle+Save can race async field
  re-validation (and the entries route never hydrates the editorialWorkflow
  slice). NOT a boolean-vs-body issue — leg-1 and the green *preview* variant both
  Save a boolean-only toggle fine. Fix: replace the bare reload with the
  PROVEN-green `reopenForPublishedDelete` remount (used by 4 green specs) — it
  bounces through the admin ROOT (fresh CONFIG_SUCCESS / re-login / editorial
  re-hydrate) and poll-reloads until Decap shows a CLEAN PUBLISHED FILE
  (editorial chip absent + "Delete published entry" present), whose settle
  windows let field re-validation finish before Save. From that clean state the
  unpublish Save takes Decap's `!unpublished` createBranchAndPullRequest path →
  a FRESH cms PR opens (layer-11a benefit preserved) → merges → URL 4xxs.
  `saveEntry` unchanged (it correctly fails on a real no-op); `TEST_TIMEOUT_MS`
  40→50 min for the remount budget. Spec-only; shim + delete_branch_on_merge
  unchanged. Also filed #109 (manage repo settings as code).

- **v0.1.42** (2026-06-29) — **#80 host-loop — `saveEntry` re-validation-race no-op
  (shared-helper hardening).** With the layer-11b remount in place, the loop's
  Save-no-op symptom proved to be a GENERAL intermittent flake, not unique to the
  unpublish leg: on run 28380065742 it hit **cms-publish-loop's cleanup** Save
  (byte-identical to the v0.1.40 run that passed → a flake, not a regression).
  Root (Decap 3.12.2 `actions/entries.ts persistEntry`): if `fieldsErrors` is
  non-empty at click time the Save `Promise.reject()`s SILENTLY (only a presence
  error toasts), and field widgets re-validate ASYNC right after a (re)mount, so a
  single Save click can land in the transient-invalid window and no-op — the form
  stays "UNSAVED CHANGES" with Save enabled until the 60s confirm times out. Fix:
  `saveEntry` (shared helper, all 6 callers) now RE-CLICKS Save inside its
  toast-or-disabled `toPass` loop whenever Save is still actionable + unconfirmed;
  once re-validation settles the click persists. Idempotent (a successful save sets
  hasChanged=false → Decap disables Save + the onClick guard no-ops, so it never
  double-persists), and a genuinely-invalid form still fails at `timeout` rather
  than masking a real error. Stacks on the v0.1.41 reopenForPublishedDelete remount.
  Spec-helper only.

- **v0.1.43** (2026-06-29) — **#82 preview-loop in-spec stale-snapshot recovery +
  cms-unpublish-republish setup self-heal.**
  - **#82:** the preview CMS loops timed out at the deploy-chain wait because the
    canary sub-PR (head `cms/*`, BASE = the parent preview-PR HEAD branch, NOT
    main) goes all-required-green + auto-merge-armed but `mergeStateStatus=BLOCKED`
    (the #1812 stale-snapshot), and the cron `cms-automerge-nudge` can't cover it
    (5-min cadence > the ~720s loop budget; it targets main.json checks + merges
    into main) (since superseded in part — see v0.1.52, which extended
    `cms-automerge-nudge.yml`'s own cron backstop to cover base!=main PRs
    directly). ROOT GAP found by audit: **none of the 5 preview specs passed
    `onBudgetExhausted`** (every prod spec does) — so their `waitForChangeReflected`
    wait had NO recovery. Fix: new shared `makePreviewCanaryRecoverer`
    (github-actions-poll.js, sibling of `makeDeployQueueExtender`) + `headChecksTrulyGreen`
    (port of the nudge's fresh-requery: stub-hazard pending-guard, ignore CANCELLED) —
    wired into every preview loop's `onBudgetExhausted`; on a green-but-BLOCKED OWN
    canary (triple guard: `cms/` head + base===preview branch + `automated-test`
    label) it forces a synchronous SQUASH `pulls.merge` into the preview branch to
    dislodge the stale snapshot. Suffix-tolerant context match (`validate-content`
    ruleset context ↔ `editorial / validate-content` check-run name). Only the legs
    with a real canary sub-PR are wired (the tags-delete leg + delete-preview DELETE
    commit directly via the shim — no sub-PR to recover).
  - **Self-heal:** a prior FAILED cms-unpublish-republish run (or the afterAll's
    fire-and-forget reset that never landed) could leave the canary `published:true`
    on main / a lingering branch / the URL serving — and the old setup THREW,
    bricking the next run (hit twice this session). Replaced the throw with
    detect-then-heal: `computeBaselineHeal` (new pure module) drives close-stale-PR +
    reset-published:false-**waiting-for-merge** + URL-404 wait, then a post-heal
    assertion that only throws if un-healable. Reuses existing helpers; logs loudly;
    only ever touches the known throw-away canary fixture.
  Spec/helper-only (no theme change). +unit tests (github-actions-poll.test.js,
  canary-baseline-heal.test.js).

- **v0.1.44** (2026-06-29) — **cms-delete-published-preview delete-leg
  editorial-limbo migration (surfaced verifying #82).** While verifying #82 on a
  PROTECTED preview branch, the delete-preview DELETE leg timed out at
  `getByRole('menuitem', /delete (published )?entry/i)` — the SAME hand-rolled
  editorial-limbo delete-click bug fixed for the prod delete specs in v0.1.39
  (layer 10), never migrated to the preview variant. Fix (PART 1, spec-only):
  migrate the delete leg to the proven `reopenForPublishedDelete` (reopen in the
  PUBLISHED state on the preview admin) + `confirmEditorDelete(() =>
  clickEditorDelete())` (dispatch-proof via a POST /git/trees watcher), after a
  `waitForMerge` on the captured seed PR; delete-leg budget via
  `makeDeployQueueExtender`; TEST_TIMEOUT 30->70 min + the workflow timeout
  35->75. The delete then LANDS on the protected multi-segment preview branch
  via the EXISTING shim delete-ref recovery — Decap PATCHes
  `git/refs/heads/${encodeURIComponent(backend.branch)}`, so a multi-segment
  preview branch arrives percent-encoded (`heads/cms%2F...`) as one raw segment
  that the shim's single-segment regex already matches (verified). DEFERRED
  (PART 2, follow-up issue): scope the shim delete-ref recovery to the configured
  backend branch (read from commit.json) so it never over-recovers a stray
  multi-segment PATCH — a safety hardening that touches the proven prod shim, so
  it is tracked separately rather than bundled here. #82's deploy-chain
  stale-snapshot recovery (cms-preview-loops, the publish/unpublish/tags legs)
  was verified green at v0.1.43; this closes the delete-preview gap.

- **v0.1.45** (2026-06-29) — **`skills-sync.yml` is now a no-op for a no-skills
  consumer (issue #83; the precondition for adamdaniel#2007-P7).** The reusable
  unconditionally `mkdir -p "$DEST"` + `rsync -a --delete`'d the platform skills
  into the consumer and opened a "Sync skills" PR — so a consumer that keeps NO
  local skills mirror (jodidaniel ships `skills-sync.yml` with no `.claude/skills`)
  got one force-created + weekly PR noise, and adamdaniel#2007-P7 could not drop
  its mirror durably (the next sync would re-create it). Fix: gate the sync on
  destination presence — `if [ ! -e "$DEST" ] && [ ! -L "$DEST" ]` (nothing at
  DEST: not a dir, file, or even a symlink) → echo + clean `exit 0`. Opt-IN by
  DEST presence; the platform never forces a mirror into existence. Preserves
  workflow-set parity (the canonical workflow stays present on EVERY consumer —
  only its behavior is data-driven; option (b) "drop it from the canonical set"
  rejected as it forks the workflow set + the parity check). Gate unit-tested
  across absent / real-dir / symlink->dir / dangling-symlink / empty-dir (skips
  ONLY on fully-absent). Workflow-only; no theme/gem change.

- **v0.1.46** (2026-06-29) — **centralize the secrets-scan + lint-staged
  pre-commit guards (dev-hooks-sync, issue #116; also unblocks adamdaniel#2007-P7).**
  The local pre-commit guards were vendored only on adamdaniel (tangled into the
  skills-mirror `bootstrap.sh`); jodidaniel had none (CI-only). The platform
  already owned canonical copies. New reusable **`dev-hooks-sync.yml`** (a
  `skills-sync` twin) down-syncs the canonical guard files —
  `scripts/{secrets-scan,lint-staged,setup-hooks}.sh`, `.githooks/pre-commit`,
  `.gitconfig-fragment` — to a consumer (PR on drift). New
  **`scripts/setup-hooks.sh`** is the slim, idempotent git-config wiring
  (`include.path`/`core.hooksPath`, NO skills) — the section-3 logic extracted
  from the old consumer bootstrap — run from a consumer `.claude/settings.json`
  SessionStart so guards are active locally. The **`dev-hooks-sync` caller** is
  added to `examples/site/.github/workflows/` → carried by the canonical-set
  parity check (auto-required on every consumer) AND seeded by the scaffolder;
  `scaffold/create-site.js` now seeds the guard files + the SessionStart wiring
  on new sites. New `e2e/dev-hooks-sync.test.js` locks the reusable FILES list ⟷
  scaffolder seed list ⟷ canonical files in lockstep (+ asserts the chain no
  longer carries the P7-removed skills-mirror guard). No theme/gem change.

- **v0.1.47** (2026-06-29) — **visual-regression PROD baseline was hardcoded to
  adamdaniel.ai (issue #123).** `e2e/regression-video.spec.js` set
  `const PROD_BASE = "https://adamdaniel.ai"`, so the regression video pipeline
  captured every changed page's PRODUCTION screenshot from Adam's site — meaning
  EVERY non-adamdaniel consumer (jodidaniel + all future sites) diffed its PR
  against a different site and always scored "visually different" (long
  misattributed to "no committed baselines"); adamdaniel worked only by
  coincidence. Fix: derive `PROD_BASE` from the consumer apex —
  `process.env.PROD_BASE_URL || (APEX_DOMAIN ? https://$APEX_DOMAIN : adamdaniel.ai)`.
  `visual-regression.yml` already exports `APEX_DOMAIN: vars.CMS_APEX` at JOB
  level, so the regression-spec step already inherits it — no workflow change.
  New `e2e/regression-prod-base.test.js` locks PROD_BASE to the apex env (never a
  bare hardcoded site). Harness-only; no theme/gem change.

- **v0.1.48** (2026-07-03) — **kill the persistent Decap "adding labels to N of
  your Editorial Workflow entries" dialog at the source.** Root cause: every
  NON-Decap writer that opens a `cms/*` PR (publish-via-auto-merge shim
  delete-recovery, `cms-fixture-pr.js` seed/remove, `sweep-stale-cms-prs.yml`
  cleanup PRs) labelled it `cms/ready` only — no `decap-cms/<status>` — so
  Decap's github backend ran its label migration on every `/admin` load for as
  long as the PR was open, and for these PRs the migration always no-ops
  ("Skipped migrating": no legacy `refs/meta/_decap_cms` metadata), so the
  dialog never cleared. Bit hard when adamdaniel #2387 (a delete-recovery PR
  with a flaky-red `e2e` check) sat open for 3 days: dialog on every prod
  `/admin` load while the flag-only daily audit went red, unnoticed, all week.
  Fix, two layers: (1) all four non-Decap `cms/*` PR writers now apply
  `decap-cms/pending_publish` at creation; (2) `audit-editorial-labels.js`
  gains `--fix` (reusable default `fix: true`, needs caller
  `pull-requests: write`) — the daily audit HEALS stragglers instead of only
  flagging them, and red now means "fix didn't stick", not "needs a label".
  Lint-locked by `e2e/editorial-label-audit-repo.test.js`; shim behaviour by
  `e2e/publish-via-auto-merge{.test.js,-browser.spec.js}`.

- **v0.1.49** (2026-07-05) — **sweep robustness + fixture-pr exports + preview-env
  concurrency + self-secrets-scan, bundled.** #127: `sweep-stale-cms-prs.yml`
  tolerates a consumer missing `_e2e/`/`_posts/`/`assets/images/uploads`
  directories (GitHub's Contents API 404s a missing-directory listing, which
  `set -euo pipefail` turned into a hard crash — jodidaniel.com's daily sweep
  had failed 30/30 times since 2026-06-06); also renamed to "... (reusable)".
  #128: `e2e/cms-fixture-pr.js` now exports `openPr`/`addReadyLabel` (their
  absence crashed `cms-tags-lifecycle.spec.js`'s cleanup safety-net with
  "openPr is not a function"). #129: job-level `concurrency` on each preview-env
  reusable's mutating job (`cms-publish-loop-preview`, `cms-preview-loops`,
  `cms-delete-published-preview`) so simultaneous dispatches against the same
  PR's preview environment stop queuing deploys N-deep past the URL-reflect
  budget; + a bounded retry on the "Delete published entry" click. #126: new
  `self-secrets-scan.yml` — the platform repo now runs `secrets-scan.yml` on
  itself (mirroring the consumer caller's PR/push/weekly-schedule triggers);
  + a consistent `(reusable)` suffix on every `workflow_call` workflow's
  display name.
- **v0.1.50** (2026-07-05) — **#130 discard `gh api` error-body stdout on
  failed listings.** Follow-up to #127 (insufficient): `gh api ... 2>/dev/null
  || true` swallows the exit code, but `gh api` still relays the HTTP error
  body to STDOUT, so a 404 captured `{"message":"Not Found",...}` into the
  variable — on jodidaniel.com (no `_e2e/`) the sweep then tried to delete a
  "file" literally named `{"message":"Not`. Fixed in `sweep-stale-cms-prs.yml`
  (the three directory listings + the Tier-3 branch-json fetch) and the
  same-class bug in `regression-review-reaper.yml`'s run/deployment listings,
  by moving the fallback OUTSIDE the command substitution
  (`files=$(gh api … 2>/dev/null) || files=""`).
- **v0.1.51** (2026-07-05) — **#131 `cms-publish-loop-preview` merge-aware wait
  + queue-aware 90-min budget** (port of #1723 Cat 1 hardening from the
  prod-mutate spec). The spec's `TEST_TIMEOUT_MS` (12min) was structurally too
  small for the real Decap → PR → nudge → merge → deploy-preview → CloudFront
  chain (confirmed-healthy real runs took 10.5-13 min and the spec still died
  at "Test timeout of 720000ms exceeded"); raised to 90min with per-leg budget
  math, mirroring the prod/delete-preview pattern.
- **v0.1.52** (2026-07-05) — **#132 preview-only PR merge fallback + nudge
  carve-out.** `cms-editorial-workflow.yml`'s `auto-merge-when-ready` now
  recovers the "Pull request is in unstable status" GraphQL error the same way
  it already handles "clean status" (a bounded ~10-min poll of the PR's own
  computed mergeable state, falling back to an explicit squash merge) — a
  `cms/preview-only` PR (base != `main`) has no required-status-check
  protection on its base branch, so `enablePullRequestAutoMerge` can never
  succeed and nothing else re-triggers this event-driven job once checks
  finish (PR #2466 sat unmerged 26+ min). `cms-automerge-nudge.yml` gains a
  `basePreviewOnly` (`baseRefName !== 'main'`) carve-out so its cron backstop
  also evaluates these PRs, whose `autoMergeRequest` can never populate in the
  first place.

- **v0.1.53–v0.1.56** (2026-07-05/06) — shipped without history entries here:
  #133 stale-docs sweep, #134 scaffolder latest-release pins, #135 preview-only
  merge unwedging, #136 dependabot re-arm sweep (see its section), #137
  platform-bump seeds newly-dictated callers, #138 base-aware nudge readiness.

- **v0.1.57** (2026-07-06) — **scheduled-run failure alerting (the silent-red
  problem).** New `scheduled-run-health.yml` reusable +
  `self-scheduled-run-health.yml` dogfood caller + `examples/site` thin caller:
  daily scan of the caller repo's last 48h of `event=schedule` runs for
  `failure`/`startup_failure`/`timed_out`, filed on a single `ci`-labelled
  tracking issue (open on first failure, run-id-deduped comments for new ones,
  auto-close after a clean window). Motivated by the 2026-07 audit: adamdaniel's
  editorial-label-audit red 24/30 days and jodidaniel's sweep-stale-cms-prs red
  30/30 for a month, all unnoticed. See "Scheduled-run health audit" section.

- **v0.1.58** (2026-07-06) — **the health-audit alert names the workflow FILE,
  not the run title.** The runs API's `name` is the run's DISPLAY TITLE — for
  this repo family the evaluated dynamic `run-name:` — so grouping by it
  produced alert headers like "scheduled — 0 12 * * *" that never said WHICH
  workflow failed (observed in the v0.1.57 dry-run against adamdaniel's real
  30-day history). `audit-scheduled-runs.js` now groups findings by
  `workflowKey()` = the workflow file's basename from `run.path`
  (`cms-publish-loop-host.yml`, …), with `name` only as a fallback when the
  API omits `path`. Lock: the groupByWorkflow unit test feeds run-name-shaped
  `name` values and asserts basename grouping.
- **v0.1.63** (2026-07-13) — **`skills-sync` no longer clobbers repo-local
  skills.** The down-sync `rsync -a --delete .cms-platform/skills/ <dest>/` made
  the site match the platform EXACTLY, so any skill a site owned but the platform
  didn't ship — adamdaniel.ai's `embeddable-tool-pages` — was deleted on every
  sync (observed as adamdaniel.ai#2593, which deleted it). The reusable now
  scans `<dest>` for skill dirs carrying a `.repo-local` marker file and
  `--exclude`s each from the rsync, protecting them from BOTH overwrite and
  `--delete` (no `--delete-excluded`). Deliberately NOT a plain "merge": unmarked
  skills stay platform-authoritative, so a skill REMOVED from the platform is
  still removed from the site — the marker is what distinguishes "site owns this"
  from "platform dropped this." The up-sync drift-guard already ignored site-only
  skills, so no guard change was needed. Lock: `e2e/skills-sync.test.js` asserts
  the reusable keeps `--delete`, discovers `.repo-local`, builds anchored
  excludes, and never passes `--delete-excluded`. Consumers opt a skill in by
  committing `.claude/skills/<name>/.repo-local` (see `skills/README.md`).
- **v0.1.64** (2026-07-13) — **`skills-sync` additive drift is no longer
  silently dropped.** The "did anything change?" gate used `git diff --quiet`,
  which is BLIND to untracked files. rsync brings NEW platform skills in as
  untracked dirs, so a purely-additive sync reported "already in sync" and
  exited without ever committing them — a latent bug the v0.1.63 repo-local fix
  unmasked (before it, `rsync --delete` always removed the *tracked* repo-local
  skill, forcing a diff that swept the additions along; adamdaniel.ai#2593 was
  exactly that). Discovered when a post-v0.1.63 sync of adamdaniel.ai correctly
  preserved `embeddable-tool-pages` but then added ZERO of the platform's 16
  canonical skills. The gate now tests `git status --porcelain -- "$DEST"`
  (untracked-aware). Lock: `e2e/skills-sync.test.js` asserts the drift gate uses
  `git status --porcelain` and never `git diff --quiet`.

- **v0.1.65–v0.1.67** (2026-07-13/22) — shipped without history entries here.
- **v0.1.68** (2026-08-07) — **the e2e suite runs as one CI job per Playwright
  project: ~680 s → ~200 s of wall clock, measured (#197).** `e2e-tests.yml` ran
  the whole suite in ONE job at Playwright's default 2 workers; it now fans out a
  `project` matrix (10 jobs, one project each, only that project's browser engine
  installed, `150%` workers) behind an aggregating `e2e` gate job — so
  `e2e / e2e` remains the single required context and NO consumer ruleset
  changed. `e2e/ci-matrix.js` derives the matrix list, each job's engine, and the
  worker count from `playwright.config.js`; `e2e/ci-matrix.test.js` fails self-CI
  if the workflow's static `matrix.project` drifts from the real project list
  (the one way the design can silently stop running a project). `--shard` was
  measured and rejected (it balances by test COUNT; a 4-way shard put 71% of the
  work in one shard), as were hand-grouped lanes and browser caching. Four
  PRE-EXISTING test-isolation bugs surfaced and were fixed — a shared upload
  basename (`e2e/upload-fixture.js`), an unbounded crawl on a fixed 30 s budget
  (`image-alt-text`), nine specs racing one `jekyll build` (`e2e/jekyll-build.js`
  + its lock test), and five `existsSync`-then-read waits on files decap-server
  was still writing (`e2e/fs-poll.js`). The reusable also stops paying for the
  per-navigation frame capture whose only consumer no reusable invokes
  (`DISABLE_PER_TEST_VIDEOS=1`). Full measurements, both job shapes, the rejected
  alternatives, and how to re-measure: **`docs/E2E-PARALLELISM.md`**.

- **v0.1.69** (2026-08-07) — **v0.1.68 follow-ups.** (1) The build lock now
  CREDITS its waiting back to the caller's test timeout: the nine build-calling
  specs run on Playwright's 30 s default with a ~4 s build, so a queue three deep
  would have traded the build race for a timeout race (not observed failing — the
  final config was green with zero flaky tests — but now structurally impossible).
  (2) `docs/E2E-PARALLELISM.md` records the CONSUMER-VERIFIED numbers from both
  v0.1.68 bump PRs (adamdaniel.ai 222 s, jodidaniel.com 148 s) plus what the
  design costs: ~1.5x the runner-minutes for ~3x less wall clock, and the wall
  clock includes GitHub allocating ten runners (3-10 s typical, once 59 s).

- **v0.1.70** (2026-08-07) — **the engine scoping reached only ONE lane, and its
  fallback was costing every other one — permanently (#202).** v0.1.68 taught
  `install-browsers-on-miss`'s globalSetup to check only `PW_PROJECT`'s engine,
  but only `e2e-tests.yml` sets that variable. Every OTHER harness-running lane
  left it unset and hit the "check all three" fallback — so a lane that installs
  **chromium only** (all ten sibling reusables) reported firefox + webkit as
  "missing", downloaded them for browsers it never launches, and printed the
  ci-runner-image-drift warning on EVERY run, making a real drift
  indistinguishable from the permanent false one. Self-CI's `node-unit-lints`
  lane, which installs NO browsers to run pure-fs lints, downloaded all three
  (~16 s/run). Both REQUIRED per-PR checks (`parity`, `preview-media`) were
  paying it. Fix: every harness step declares its project(s) via `PW_PROJECT`
  (`neededEngines()` takes a comma-separated list), locked by
  **`e2e/engine-scope-lint.test.js`** — a step whose `PW_PROJECT` is missing or
  disagrees with its `--project` flags fails self-CI, so a new lane can't
  regress it. Steps running a different config (visual-regression, whose config
  declares no globalSetup) are explicitly exempt. Also: **tag routing is opt-IN, so
  an untagged admin spec matches every public project's `grepInvert`** —
  `cms-html-embed.spec.js` drove Decap untagged, held to one project only by a
  hand-rolled `beforeEach` gate (so the harm was mis-stated at the time as "it ran
  on all eight"; see the third paragraph, where leaving that gate in place turned
  out to be the real bug). Now `@admin-write`, with
  **`e2e/admin-tag-lint.test.js`** (AST) failing any spec that navigates the admin
  shell untagged. Plus four documentation corrections
  from v0.1.68's per-project → uniform-`150%`-workers pivot (the
  `playwright.config.js` `workers:` comment, an AGENTS.md self-contradiction,
  `docs/E2E-PARALLELISM.md` naming two symbols that don't exist, and
  `jekyll-build.js` mislabelling its nine callers).

  Also in v0.1.70, from an adversarial review of the parallelism work's own
  fixes: **the build lock's stale break was unreachable** (`STALE_MS` 300 s >
  `WAIT_TIMEOUT_MS` 180 s, so a fresh waiter always timed out before it could
  break an orphaned lock — a killed worker wedged the next build, the opposite of
  the documented guarantee) and **breaking/releasing it was not ownership-checked**
  (a merely-slow holder could have its lock broken, and its `finally` would then
  delete the NEW holder's lock); **six more specs still polled a file's EXISTENCE
  and then read it**, and in `cms-html-embed`/`cms-inline-image` that read feeds a
  `writeFileSync` back to the same path, so an empty read overwrote the entry with
  front-matter-less content instead of merely failing an assertion; and
  **`cms-page-crud` left an orphaned `<loc>` in the shared `_site/sitemap.xml`**
  that `image-alt-text`'s hard 200 assertion crawls (its `/blog/e2e-…` fixture
  exemption does not cover a `/pages/…` path). Each is now lint- or test-locked:
  `jekyll-build.test.js` asserts the constants' inequality and the ownership
  refusal, `fs-poll-lint.test.js` (AST) fails the build on the read-race shape,
  and the sitemap prune mirrors `cms-publish-flow`'s.

  Also **the browser install is now BOUNDED and RETRIED (#204).** Measured on
  adamdaniel.ai job 92862768030: `npx playwright install --with-deps webkit` took
  **39 minutes** while the tests it installed for took 41.6 s — the Ubuntu mirror
  served that runner at ~35 KB/s for its whole run and the install had no upper
  bound. Fanning out to ten lanes means ten INDEPENDENT apt exposures per run, and
  the aggregating `e2e` gate waits for the slowest, so that one lane held a
  delete-recovery PR open 40 min and blew the media-roundtrip loop's 30-minute
  delete-leg budget — the loop failed on a green test suite. All 13 call sites now
  go through `.github/actions/install-playwright-browsers` (`timeout 420` per
  attempt, 3 attempts), locked by **`e2e/playwright-install-bounded.test.js`**. A
  bare `timeout-minutes:` would be WORSE — it turns a slow mirror into a RED
  required check, blocking a `cms/*` canary PR permanently instead of merging it
  late; only a retry recovers, because a fresh attempt gets fresh connections.
  (A later release removed the bound from the apt half specifically: bounding it
  orphaned a root-owned `apt-get` that then starved every retry on the dpkg lock
  — job 92989057569. See the "NEVER shell out" bullet above for the current
  two-phase design.)

  One more, and it was a REGRESSION from #202's own tagging: `cms-html-embed`
  carried a hand-rolled `beforeEach` gate skipping unless the project was
  `chromium-desktop-1080`, so the new `@admin-write` tag (which routes to
  `chromium-desktop-3k`) made the two conditions mutually exclusive and **the
  whole file skipped everywhere** — the kramdown render contract silently
  untested, with nothing red. The gate is gone (the tag expresses that routing),
  and `admin-tag-lint.test.js` now derives each spec's routed projects from the
  config's own `grep`/`grepInvert` and fails on an unsatisfiable gate. **A tag is
  routing: never leave a hand-rolled `project.name !== "…"` skip beside one.**
  (That gate also means #202's "it ran on all EIGHT public projects" overstated
  the harm — the gate had held it to one; the tag was still the right fix.)

- **v0.1.71** (2026-08-07) — **one doc file on a bump PR was cancelling a prod
  loop (#208).** The bump-skip (#57) required EVERY changed path in a push to be a
  version pin, so the `AGENTS.md` corrections landed on the v0.1.70 bump PR — the
  natural place for a doc fix that goes with a bump — made `every(isBumpArtifact)`
  false. The gate said RUN, **all three prod loops fired on the same push**, and
  because they share the `prod-mutating-loop` group (which holds an in-flight run
  but DROPS a co-arriving sibling), `cms-media-roundtrip`'s heavy job was
  **cancelled outright** (adamdaniel.ai run 31185014802) — as was
  `cms-publish-loop-prod`'s (run 31185015141) — while `cms-publish-loop-host`'s
  survived. **#70's disjoint-push-triggers fix cannot prevent this**: a bump
  rewrites the `uses:@<ref>` pin in EVERY loop's own workflow file, which IS each
  loop's own trigger path, so a bump inherently fires all three and the skip is
  the only thing between a bump and a cancelled loop. `isBumpOnlyPush` now also
  tolerates paths that cannot change the built site (`AGENTS.md`, `CLAUDE.md`,
  `README.md`, `LICENSE`, `docs/**` — exactly the deploy workflows'
  `paths-ignore` set); a bump carrying `_posts/`, a script, a config or CSS still
  RUNS. Both directions locked by `e2e/cms-recursion-churn.test.js`. Also: the
  measured per-lane ceiling analysis in `docs/E2E-PARALLELISM.md` (the long pole
  is WebKit's TEST speed, and sharding within a project buys ~45 s for double the
  job count — priced, and declined), the apt-stall frequency (~1 run in 10, two
  occurrences in one afternoon), and both consumers' AGENTS.md corrected where
  they still claimed per-project worker counts.

- **v0.1.72** (2026-08-08) — **the apt bound orphaned a root-owned `apt-get`
  (#216), plus the locale-dependent renderer (#213).** v0.1.70's install bound
  wrapped the WHOLE `install --with-deps`, and that did not abandon a slow apt —
  it ORPHANED one. Playwright logs "Switching to root user to install
  dependencies..." before shelling out, so the `apt-get` doing the work is a
  **root-owned grandchild**; an unprivileged `timeout`'s signal cannot reach it
  (EPERM) however the process group is arranged, which means `setsid` plus a
  group kill does not help either and **no signal-based kill can**. Measured on
  adamdaniel.ai job 92989057569: attempt 1 fetched for 7 minutes with ZERO
  lock-wait lines (it owned the dpkg lock), was killed mid-transaction at the
  420 s bound, and 19 s later attempt 2 died on "Could not get lock
  /var/lib/dpkg/lock-frontend. It is held by process 2857 (apt-get)" — attempt
  1's own survivor, not the runner's `apt-daily`. That failed the webkit lane,
  failed the `e2e` gate, BLOCKED canary PR #2978 and timed out the prod loop; a
  re-run with zero code change went green. Fix: the install splits into two
  phases — `install-deps` (apt) retried but **never** wrapped in `timeout`, and
  `install` (the download, no `--with-deps`) keeping the escalating bound. The
  trade is deliberate: apt IS the slow phase, so a lane can finish late, and
  late-and-green beats red-and-blocked because a red required check blocks a
  `cms/*` canary PR permanently. Classification now greps the captured output
  for `Could not get lock|lock-frontend|dpkg was interrupted` BEFORE reading the
  exit code, since `npx playwright install` wraps apt's 100 as 1.
  Also: **#213** — `scripts/render-decap-config.rb` inherited
  `Encoding.default_external` from the ambient locale, so with no `LANG` it
  resolved to US-ASCII and the first `sub` over `config.base.yml`'s UTF-8
  em-dashes raised `invalid byte sequence in US-ASCII`. CI masked it
  (`ubuntu-latest` sets `LANG=C.UTF-8`); a deploy-time renderer must not depend
  on that. Pinned in the CLI entry point (covering its reads/writes, both
  `YAML.load_file` calls, and the `require_relative`'d `FieldLibrary`), NOT in
  the Jekyll-hosted twin, which must not mutate its host's globals. Proven
  output-neutral under a UTF-8 locale, so no consumer's admin config shifts.
  Plus **build-lock hardening (#214)**: `release()` refuses unless the owner
  reads back exactly our token (an unreadable owner used to fall through and
  delete a lock it could not prove was ours); the stale branch no longer
  `continue`s past the deadline check (an unbreakable lock used to spin
  `acquire()` forever — a hang is worse than a timeout); and the lock wait is
  credited to the caller's test budget INCREMENTALLY, so acquire's own
  diagnostic can surface before Playwright kills the test. The "every in-test
  jekyll build goes through the helper" lint was a regex matching one call
  shape and is now an AST detector over the whole exec/spawn family.

## Consumers

- **adamdaniel.ai** — consumer #1, user-owned, the dogfood. Migrated to
  gem-delivered admin (PR #1883); live prod `/admin` verified. Daily
  editorial-label-audit adopted. (A loop co-arrival fix #1892 narrowed the host
  publish-loop's push trigger to its own canary surfaces so it stops evicting
  prod-mutate in the shared `prod-mutating-loop` concurrency lane — see agent
  memory `cms-prod-loops-no-concurrent-runs`.)
- **jodidaniel.com** — consumer #2, org-owned, a SINGLE-PAGE bio. `/admin`
  restructured into 9 per-section collections (5 folder collections ordered by a
  numeric `weight`, declared `output:false`; 4 file collections reading
  `_data/*.yml`). `cms.base_collections: []` hides the generic collections. A
  live-gate in `_data/settings.yml` `site_live` (default `false`) keeps prod
  coming-soon with zero bio leak. Go-live is tracked in jodidaniel issue #26. Its
  token-driven CMS automation (cms-automerge-nudge, auto-resolve-newline-conflict,
  sweep-stale-cms-prs) runs on a provisioned **`CMS_E2E_PAT` repo secret**; the
  scheduled-workflow failures observed through mid-2026-07 were actually the
  sweep/reaper bugs fixed in v0.1.49-v0.1.51 (missing-directory-listing crash
  #127, `gh api` error-stdout capture #130), not a missing secret.

## Roadmap / open issues

- **issue #5 GOAL 1 — admin consolidation: DONE** in v0.1.4 (this is the
  gem-delivery model documented above).
- **issue #5 GOAL 2 — `field_library` + `$ref` reuse: DONE (LOW-RISK increment).**
  A site's seam `collections.site.yml` can `$ref` platform field defs from
  `theme/admin/field_library.yml`, resolved at render-time in BOTH paths via the
  shared `CmsPlatformTheme::FieldLibrary` resolver (see "field_library + `$ref`
  reuse" above). The base config stays TEXT (spliced byte-for-byte; all
  verbatim-locked lines preserved); no-`$ref` seams render byte-identically
  (backward-compat proven). **Still deferred:** the full base-collection-override
  **deep-merge** (override/reorder a base collection's fields) — the seam remains
  append-only; `$ref` delivers shared-field REUSE only.
- **issue #21 — DONE (v0.1.13, #39):** the prod-mutate canary URL not reflecting
  was CloudFront NEGATIVE-CACHING the pre-create 404 (`ErrorCachingMinTTL: 300`);
  fixed to `0` in the bootstrap template + verified live (both prod
  distributions). Empirically confirmed: a canary deployed and its `/blog/<slug>/`
  served 200. See the `aws-bootstrap` skill. (The loops' DELETE leg was a separate
  follow-up — #45 / adamdaniel#1815 delete-phase.)
- **issue #22 — DONE:** publish loops now prune their own orphaned `cms/e2e*` /
  `cms/posts/2099-*` canary branches (scoped, only branches with no open PR;
  locked by `e2e/workflow-loop-branch-cleanup.test.js`).

## Environment gotchas (this machine / web)

- **The local checkout can be STALE/detached** — before any analysis or work,
  `git fetch && git checkout main` (or compare against `origin/main`), then branch
  off `origin/main`. An old checkout may not reflect landed migrations (e.g. the
  `admin/` → `theme/admin` move, the gem-delivered admin model) and you'll reason
  about machinery that no longer exists. Verify HEAD == `origin/main` first.
- The **web** GitHub MCP connector can't create repos (403); `/teleport` to local
  and use `gh` (authed as Adam-S-Daniel, scopes incl. `repo`,`workflow`).
- Background sessions: editing a non-cwd repo checkout trips a worktree-isolation
  prompt on the Edit/Write tools — write via Bash (`cat >`, a Python pass) which
  isn't tool-guarded. Writing `.claude/settings.json` is blocked as self-mod.

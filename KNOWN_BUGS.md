# KNOWN_BUGS.md

The existing bug pile, made legible by Group A of the bug-trap
(see `BUG_TRAP_PUNCHLIST.md`). Generated 2026-05-25 from the first
full-suite run after Items A.1–A.6 landed.

**Don't fix bugs from this list during Group A.** Fixes come after
the trap is in place. For each entry: severity, reproducer
command, browser scope, and best-current-guess at root cause.

Each bug carries a `[real]` or `[test]` tag distinguishing
"the app is broken" from "the test we wrote is broken".

**Run-of-record summary:** 148 passed, 22 failed across the full
suite on Chromium + WebKit-mobile (11.5 min wall clock). Of the
22 failures: 4 were Chromium-only, 18 were WebKit-only or both —
exactly the gap pattern the trap was built to surface.

**Reproduction pass — 2026-05-25 (HEAD: `3f47e67`):** all 11
entries re-run against current main. **11/11 still reproduce as
described** — none closed by intervening commits, none partially
fixed. Per-entry status added below.

---

## A11Y-1 — axe color-contrast: themed eyebrow/muted labels + Claude panel `[real, serious]`

**Source:** the axe-core a11y tier (QA_COVERAGE_SYSTEM_SPEC §4 build-list #2),
wired 2026-05-31 at HEAD `fcf691a`. axe scans the SETTLED page (the helper
collapses entrance animation/transition durations before analyzing), at the
serious+critical WCAG-2 AA threshold. These are genuine, stable findings — NOT
the animation-transient `fade-up` artifacts (those were eliminated by the
settle step).

**Status: [real, recorded — do NOT fix now].** Folds into the M6 theme pass —
the same cycle that fixes the Claude-in-app wrong-theme bug. The axe tests
allowlist `color-contrast` on these two surfaces (referencing this entry) so the
gate stays green and still catches every OTHER serious/critical rule; Phase 3 /
M6 removes the allowlist to re-gate contrast once the palettes are fixed.

**Findings (chromium; WCAG AA needs 4.5:1 normal / 3:1 large text):**
- **Claude-in-app panel — ALL personas** (2 nodes): muted ink `#696F68` on
  linen `#F2EFE7` = **4.48:1** (just under 4.5). This is Helen's M1 panel
  palette (`T.inkMuted` in `ClaudeChat.jsx`), which every persona inherits
  because the panel is hardcoded Helen (the wrong-theme bug). axe thus
  **corroborates the theme bug from the contrast angle** — a real tier overlap
  (a11y ↔ the known Claude-in-app theme finding). Nodes: the trip-title eyebrow
  (JetBrains Mono 10px) + a message-bubble line.
- **Trips index — persona-variant** (themed mono "eyebrow" labels + muted italic):
  - **jonathan**: oxblood `#A33A2E` on near-black `#0E0F11` = **2.92:1**.
  - **aurelia**: hot-pink `#E8478C` on pale-pink `#FCE8EE` = **3.13:1**.
  - **helen**: muted `#696F68` on linen `#F2EFE7` = **4.48:1**.
  - **rafa**: clean (no serious/critical).

**Reproducer:** `cd app && npx playwright test a11y-axe --project=chromium`
(temporarily drop `allow: ['color-contrast']` in `tests/e2e/a11y-axe.spec.js`,
and/or `RT_PERSONA=<traveler>` to scan a specific theme).

**Non-vacuous:** the tier is proven to catch real violations (these) and an
injected `button-name` (critical) survives the contrast allowlist (see the
commit that added the tier).

---

## DEADCODE-1 — orphaned pre-refactor component/data/hook layer (78 files) `[real, dead-code]`

**Source:** the dead-code tier — knip (QA_COVERAGE_SYSTEM_SPEC §4 build-list #3),
wired 2026-05-31 at HEAD `14ab6a0`. Reproducer: `cd app && npm run deadcode`.
knip builds the real module graph from the production entry (index.html →
src/main.jsx → App.jsx) plus the test/script/worker entries; anything in
`src/**` not reachable is reported. Non-vacuous: the 3 known orphans appear AND
live code (JonathanView + its imports Avatar/NearbyResultsModal/FlightStatus) is
NOT flagged; spot-checks confirmed each flagged file's only importers are other
orphans.

**Status: [real, recorded — do NOT delete in this pass].** Cataloging is the
job; deletion (or restoration) is a separate triage decision.

**Root cause:** the "four refined themed views" refactor (commit `1fc7a9f`)
replaced a prior single-view design generation; the old layer it used was left
mounted-by-nothing — one connected dead subgraph (DiscoverView →
StopCard/RouteMapLazy → …; ItineraryView → NextUpCard/useVisited → …). Live views
import a different, smaller set.

**RESTORE-vs-DELETE flags (do NOT resolve here):**
- **`src/hooks/useTheme.js`** — dead (no live importer), BUT it holds the
  per-person PWA **manifest + icon + theme-color/apple-title swap** logic.
  App.jsx now sets only `data-theme` inline, so that per-person install capture
  is NOT running — a POSSIBLE silent PWA-install regression. Likely a RESTORE
  (re-wire into App), not a delete. (Its deps `src/data/themes.js`,
  `src/utils/appIcon.js` are also flagged.)
- **Map cluster** — `RouteMap.jsx`, `RouteMapLazy.jsx`, `RouteSvg.jsx`,
  `MapCard.jsx` + the unused deps **`leaflet`** + **`react-leaflet`**. A whole
  map feature went dark in the refactor. Restore-vs-delete; if delete, drop the
  two deps to shed install/bundle weight.

**Unused files (78), by dir:**
- views (1): RoadSearch.jsx
- components (37): ActualLog, AudioMemo, BottomNav, CeremonyMorningOptions,
  DayOrientationBanner, DiscoverView, DriveTimeCalculator, EmergencyFab,
  EssentialsCard, FilterBar, FlightHomeCard, GasWarning, HoustonFriday,
  ItineraryView, JonathanQueue, KennedaleDay, MapCard, MediaView,
  MondayWeatherCard, NavBar, Navigation, NextUpCard, PersonSelector,
  PodcastSection, PrepCard, RePlan, RiskWatch, RouteMap, RouteMapLazy, RouteSvg,
  ShareButton, StopCard, ThursdayDriveBox, TomorrowHeadsUp, TonightCard,
  TripView, YouTubeSection
- data (21): actualSeed, ceremonyOptions, curatedStops, essentials,
  flightScenario, gas_warnings, jonathan_podcasts, kennedale, meta, mileage,
  overnight, podcasts, preferences, prep, riskFlags, route, stops, themes,
  tripCalendar, verifiedStops, youtube
- hooks (9): useDismissed, useGeolocation, useItineraryFilters, useOnlineStatus,
  useSwipeDays, useTheme, useVisited, useWeatherPath, VisitedContext
- utils (10): actualLog, appIcon, driveTime, filterStops, navLinks, quickSearch,
  riskWatch, scoreStop, share, tripDay

**Unused dependencies (2):** `leaflet`, `react-leaflet` (the dead map cluster).

**Unused exports (21)** — exported but imported nowhere, in OTHERWISE-LIVE files
(dead exports; lower severity than dead files): ClaudeChat.jsx `ClaudeMark`,
`ClaudeLockup`; claudeChat.js `createConversation`; flightStatus.js
`airlineStatusUrl` (also a duplicate-export alias of `flightAwareUrl`);
icsExport.js `buildIcs`; leaveWhen.js `clearLeaveWhenCache`; memAssets.js
`deleteAsset`; memoryStore.js `loadOwnMemoryForStop`; openState.js `formatTime`;
photoBackfillUpload.js `mergeRefIntoExisting`; photoEntries.js `refUrl`;
photoPipeline.js `PHOTO_MAX_EDGE`, `PHOTO_JPEG_QUALITY`, `validatePhotoFile`,
`readExif`, `downscaleImage`; uploadQueue.js `list`, `remove`, `update`,
`clear`; whisper.js `transcribeAudio`.

**Noise / not-real (documented, not findings):**
- Unresolved import (1): `tests/e2e/photos-auto-downscale.spec.js` does
  `import('/src/lib/memAssets.js')` (absolute-path dynamic import — a DEV-only
  test hook, ref KNOWN_BUGS R2); knip can't resolve it. Harness pattern, not
  dead code.
- Config hints (4): knip flags `src/main.jsx` / `vite.config.js` /
  `playwright.config.js` as redundant entries (it auto-detects them) + a generic
  "78 unused files — add an entry?" nudge. The redundant-entry hints are
  cosmetic; the "add entry" nudge is a FALSE alarm here (the 78 are verified
  genuinely dead, not a missing-entry artifact). Config left explicit for
  clarity.

---

## Phase 3 — Slice C1: themed spine (S1 Trips index · S2 Trip home · S3 Stop detail) `[capture log]`

**Walked 2026-05-31, HEAD `d107f77`, all 4 personas** (jonathan/helen/aurelia/rafa).
**Tiers run (existing only, per the Phase-3 scope call):** pw (smoke + visual-baselines),
axe. instrument N/A — read-only surfaces emit no `rt_upload_log_v1` entries. sim:
existing specs don't walk the spine per-persona (see C1-GAP-3).

**Result: NO new `[real]` bugs on the themed spine.** S1 + S2 theme correctly across
all four personas; the Claude-in-app wrong-theme bug stays bounded to its surface
family (C2 — O1/O2), NOT the trip view. Inherited **A11Y-1** (contrast) reproduces and
is the only spine finding — allowlisted, deferred to M6.

**Confirmations (non-vacuous, real runs):**
- **S1 axe ×4 — all green** at serious+critical (color-contrast allowlisted to A11Y-1).
  Closes a real hole: **Aurelia + Rafa trips-index a11y were zero-coverage pre-Phase-2**
  (axe defaulted jonathan); now scanned, nothing serious/critical beyond known contrast.
  Repro: `RT_PERSONA=<p> npx playwright test a11y-axe --project=chromium -g "trips index"`.
  Tiers caught: axe.
- **S2 visual ×4 — all green** vs committed per-persona baselines (`trip-{persona}.png`)
  → the themed trip view renders correctly per persona. Repro: `npx playwright test
  visual-baselines --project=chromium -g "themed trip view"`. Tiers caught: pw(visual).
- **S1 boot** (smoke, jonathan: app boots → lands on `volleyball-2026` → 4-traveler
  switcher renders) + **S1 trips-list** visual (helen) — green.

**Gaps recorded (capability ≠ walked — these ARE Phase-3 outputs per spec §3):**
- **C1-GAP-1 `[gap, S3 Stop detail]`** — **zero walked coverage.** No existing spec
  renders the `stop` view (`StopDetail`); axe/visual/sim none wired. Capability says
  pw/sim/ax/chrome can reach it; nothing does. Close with a stop-detail render+axe walk
  (spec-authoring — deferred to triage per the Q2 scope call).
- **C1-GAP-2 `[gap, S2 contrast]`** — axe is wired on trips-index + the Claude panel
  ONLY, not the trip-view body; per-persona WCAG contrast on S2 is unmeasured (the
  visual ×4 covers layout/theme, not contrast ratios). Close by extending a11y-axe to S2.
- **C1-GAP-3 `[gap, sim spine]`** — existing sim specs don't render the spine
  per-persona on real iOS (`smoke.test.mjs` is persona-agnostic plumbing at `:5181`;
  photo-render/offline-drain/video-encode are photos/C3). Booted iPhone 17 / iOS 26.5
  is available; a persona-parameterized spine sim spec would close it (deferred).

---

## Phase 3 — Slice C2: Claude family (O1 panel · O2 confirm cards, 6 types) `[capture log]`

**Walked 2026-05-31, HEAD `21425f9`, all 4 personas.** Tiers run (existing only): pw
(claude-* behavior specs), axe (panel, persona-aware), security (render-xss + markdown
guard), instrument (harvestDevLog — see C2-GAP-1). **C1 proved the rest of the spine
themes correctly per-persona; C2 confirms the wrong-theme bleed lives HERE, at its source.**

### P3-01 — Claude panel + cards render Helen's hardcoded palette for ALL personas `[real, S2 — deferred M6]`
- **Surface×persona:** O1 (`ClaudeChatPanel`) + O2 (`ConfirmCard`, all 6 card types) ×
  **jonathan / aurelia / rafa** (helen renders correct *by coincidence* — it IS her palette).
- **Direct evidence (code = source of truth for what renders):** both files define a
  module-level `const T` = Helen's linen/sage palette — `ClaudeChat.jsx:43-54`
  (`bg #F2EFE7`, `ink #15201A`, `inkMuted rgba(21,32,26,0.62)`, `accent #2E5D3A` sage) and
  `ConfirmCard.jsx:27-48` ("Helen's linen palette (duplicated from ClaudeChat.jsx)").
  Applied via **inline styles only**, with **no read of `data-theme`/persona/CSS-vars**.
  S1/S2 theme via `data-theme` CSS vars (C1, green ×4); O1/O2 bypass that entirely →
  jonathan/aurelia/rafa get Helen's colors inside their otherwise-correctly-themed app.
  Comments name it: *"Helen's linen palette is the M1 default for everyone — Jonathan's
  dark-editorial skin lands in M6."*
- **What SHOULD render** (the per-persona themes the spine already uses, per A11Y-1):
  jonathan dark-editorial (oxblood `#A33A2E` on near-black), aurelia hot-pink
  (`#E8478C`/`#FCE8EE`), rafa his own palette, helen linen. The panel renders helen's for all.
- **Tiers caught:** code-read (direct render evidence) + **axe** (A11Y-1: panel **4.48:1 =
  `T.inkMuted` over `T.bg` for ALL personas** — the contrast symptom corroborates the
  render bug; tier overlap a11y ↔ theme). Cross-ref **A11Y-1**.
- **Reproducer:** `RT_PERSONA=jonathan npx playwright test a11y-axe --project=chromium -g
  "Claude-in-app panel"` (drop the `color-contrast` allow to watch Helen's 4.48:1 fire
  under jonathan); or read `ClaudeChat.jsx:43` / `ConfirmCard.jsx:29`.
- **Non-vacuous:** C1 proved the rest of the app themes correctly per-persona, so this is a
  real *localized* outlier, not a global theming failure. **DO NOT FIX — M6** rewires the
  panel/cards to read `TRAVELERS[persona].theme` instead of the hardcoded `T`.

### Confirmations (green, real runs)
- **O1/O2 behavior — 22 passed** (pw, chromium): all 6 card types + panel states (entry,
  stream, past-convo list, error, mode-shift, apply-failure-plain-language). Behavior is
  persona-invariant by design — the bug is purely visual/theme, **not logic**. Tiers: pw.
- **Render sanitization PASSES on its home surface:** `security-render-xss` green (model
  HTML renders inert — no element, no execution, escaped); `markdown-path-guard` 4/4 (no
  XSS-capable imports, react-markdown present, no `rehype-raw`). Tiers: security(render).
- **axe panel ×4 — all green** (serious+critical, contrast allowlisted). Panel was
  axe-scanned jonathan-only pre-Phase-2; **helen/aurelia/rafa panel a11y now scanned, clean.**
  Tiers: axe.

### Gaps recorded
- **C2-GAP-1 `[gap, O2 instrument]`** — instrument-harvest not wired on the Claude card
  surface. `ConfirmCard` logs to the dev-log on apply-failure (`ConfirmCard.jsx:1063`), but
  the only existing harvest spec (`instrumentation-harvest.spec.js`) walks photos, not cards.
  On the successful behavior walk the failure-only dev-log stayed empty (no silent failures).
  Close by harvesting during a card-apply-failure walk (spec-authoring — deferred per Q2).

---

## R1 — Lightbox touch gestures don't run on WebKit `[test, S2 → resolved]`

**Status (2026-05-25): [resolved]** — Pure test fix. WebKit
blocks both `new TouchEvent(...)` and `new Touch({...})` with
`Illegal constructor`. Playwright's `Touchscreen.tap()` only
fires at a single coordinate, so it can't synthesize a swipe.
But the React handler in PhotoAlbum.jsx only reads
`touches[0].clientX/Y` (touchstart) and
`changedTouches[0].clientX/Y` (touchend) — it doesn't listen for
touchmove. So we sidestep both restricted constructors by
dispatching a base `Event` and pinning `touches` /
`targetTouches` / `changedTouches` via `Object.defineProperty`.
React's event delegation listens by event name and reads touches
off the native event, which is enough.

**Spec:** `tests/e2e/photos-lightbox-swipe.spec.js`
**Reclassification:** Was `[real, S2]` with DESIGN-DECISION risk
(the carryover allowed for the possibility the app's swipe
detector needed work). Now confirmed `[test]` — no app change
required. Verified 4/4 green on both projects.

---

## R2 — saveAsset auto-downscale tests fail on WebKit `[test, S3 → resolved]`

**Status (2026-05-25): [resolved]** — Investigation refuted the
carryover's Vite-URL hypothesis. Switching the dynamic import to
a window-global hook (DEV-only) made the import succeed, but
`saveAsset` then failed at `IDBObjectStore.put({...blob})` —
exactly the R4 IDB+Blob bug. R2 is downstream of R4, same engine
limitation, same skip pattern.

**Fix:** `test.skip(browserName === 'webkit', WEBKIT_IDB_BLOB_REASON)`
on all 3 tests, reusing the shared reason text from R4a. The
in-page dynamic import is preserved (works on chromium); no app
change needed. The Simulator gate's `offline-drain.test.mjs`
covers IDB+Blob storage on the iOS-real surface.

---

## R3 — WebCodecs video pipeline doesn't render preview on WebKit `[real, S1]`

**Status (2026-05-25): R3a + R3b [resolved]** — Both shipped.
The R3b Simulator journey did its job: it surfaced a real iOS
Safari bug in our encode pipeline that the Playwright suite
never caught. Specifically:

  1. iOS Safari's WebCodecs `VideoEncoder` doesn't auto-compute
     chunk duration from consecutive frame timestamps the way
     Chromium does. Without an explicit `duration` on the input
     `VideoFrame`, the output chunk's duration is unset and
     `mp4-muxer.addVideoChunk` rejects with "duration must be a
     non-negative real number". Fixed in
     `app/src/workers/encodeVideo.worker.js` by stamping every
     VideoFrame with `duration: frameDurationUs`.

  2. iOS Safari's `requestVideoFrameCallback` can fire with a
     repeated or non-monotonic `metadata.mediaTime` for some .mov
     files. Even with the duration fix, that produces 0 / negative
     chunk durations downstream. Fixed in
     `app/src/lib/videoPipeline.js` `walkAllFrames` by clamping
     timestamps to strict monotonicity (lastTs + 1µs floor).

R3a's skip pattern remains in `photos-video.spec.js` because
Playwright's bundled WebKit still can't drive the synthetic
pipeline (the failure mode is upstream of these app bugs —
input synthesis itself stalls). The iOS-real surface now has
explicit coverage via `tests/simulator/video-encode.test.mjs`
which passes against booted iPhone 17 / iOS 26.5 (~12s).

**Spec:** `tests/e2e/photos-video.spec.js`
**Browsers:** webkit-mobile (chromium OK)
**Symptom:** `dispatch-preview-video` element never visible
within 60-second timeout.

**Root cause hypothesis:** Playwright's bundled WebKit doesn't
ship full WebCodecs. The dispatch composer detects WebCodecs
unavailability at modal-open time (per the M3 design) and hides
the video picker, but the test fixture still tries to invoke it.

**Severity S1 because:** this is the exact iOS WebCodecs gap
called out in `tests/e2e/_fixtures/withTrip.js` comments and in
`PUNCHLIST_3.md`. Real iOS Safari 17+ DOES support WebCodecs
basics; whether the simulator/Playwright WebKit does is a real
production-relevance question.

**Reproducer:** `npx playwright test tests/e2e/photos-video.spec.js --project=webkit-mobile`

**Fix path:** First clarify whether Playwright's WebKit
intentionally ships without WebCodecs (likely yes — it's a
build-time flag). If so, this test should `test.skip()` on
webkit-mobile and rely on Item A.6's Simulator gate for real
iOS Safari WebCodecs coverage.

---

## R3c — Chromium gate extension: vite cold-cache module-resolution race `[test, S2 → gated, ongoing]`

**Status (2026-05-26): [gated, ongoing]** — Test-harness
limitation, NOT an app bug. The chromium leg of
`photos-video.spec.js:43` started failing reproducibly on cold
cache after the markdown-rollback chain landed in `72ad418`
(react-markdown@9 replacing marked + dompurify). Mechanism is
characterized; the fix shape that would close it cleanly is
unknown.

**Root cause:** vite's cold-cache module-resolution race against
the encode worker. `app/src/workers/encodeVideo.worker.js`
imports `mp4-muxer`. The worker is loaded via
`new Worker(new URL('../workers/encodeVideo.worker.js',
import.meta.url), { type: 'module' })` from
`app/src/lib/videoPipeline.js:88`, which runs during the test's
`setInputFiles → onVideoChange → encodeVideo` chain. mp4-muxer
isn't pre-bundled, so vite discovers it as a new dependency
mid-request, re-runs optimizeDeps, and emits a full-page reload
to pick up the new bundle. The page resets to its initial
'trip' view, the modal unmounts, and the locator wait for
`dispatch-preview-video` times out.

**Confirmation:** cold-cache diagnostic captured `[vite]
connected.` TWICE in the console (definitive evidence of a
mid-test page reload). Encode itself works — same test passes
in 5s with a warm cache.

**Fix attempts that did NOT work (2026-05-26):**

1. **`optimizeDeps.include: ['mp4-muxer']`** — broke ALL cold-
   cache tests at React hydration. mp4-muxer references
   WebCodecs primitives (`VideoEncoder`, `EncodedVideoChunk`,
   etc.) that don't exist on the main thread; bundling it into
   the main-thread context via esbuild starves the page-load
   path enough that React doesn't hydrate within the 30s test
   budget. Even smoke.spec.js failed 2/2.

2. **`server.warmup.clientFiles:
   ['./src/workers/encodeVideo.worker.js']`** — same shape as
   (1). 30+ tests failed at hydration on cold cache before the
   run was killed. `clientFiles` transforms the worker file as
   a client-context module, which means mp4-muxer's main-
   thread bundle still gets generated.

Don't retry either shape. The right fix would need to either
(a) tell vite the file is a worker without forcing main-thread
bundling, (b) discover the worker dep graph eagerly without
bundling, or (c) sidestep the discovery race some other way.
None of those were obvious in the docs / config surface I
checked.

**Real coverage:** the R3b Simulator journey at
`app/tests/simulator/video-encode.test.mjs` exercises the
encode pipeline against a real iOS Safari + real .mov fixture
in ~12s. That's strictly stronger coverage than the Playwright
synthetic, so the gate doesn't reduce production confidence.

**Gate:** `test.skip(browserName === 'webkit' || browserName
=== 'chromium', ...)` on `photos-video.spec.js:43`. The other
tests in the same file (`19`, `167`) remain gated only on
webkit-mobile — they don't hit the encode worker, so the cold-
cache race doesn't apply to them.

**Spec:** `tests/e2e/photos-video.spec.js`
**Browsers gated:** chromium + webkit-mobile (both projects)
**Reproducer:** `rm -rf app/node_modules/.vite &&
cd app && npx playwright test tests/e2e/photos-video.spec.js:43
--project=chromium` (skip-removed) — modal opens, encoding
panel appears, then `[vite] connected.` fires a second time
and the page is gone.

---

## R4 — Offline sync-pill never surfaces on WebKit `[test, S2 → resolved]`

**Status (2026-05-25): [resolved]** — Classified as a
Playwright-WebKit quirk, NOT a real iOS bug. Verified via
Simulator diagnostic: real iOS Safari (iPhone 17 / iOS 26.5)
round-trips Blobs through IndexedDB cleanly; Playwright's
bundled WebKit fails `IDBObjectStore.put({...blob})` with
"Error preparing Blob/File data to be stored in object store".
The app's enqueue path correctly catches the failure and logs
it (code: `storage-quota`, phase: `queue-insert-failed`), so
the queue stays empty and the pill correctly doesn't render —
the test's assertion is the wrong shape for this engine.

**Fix:** `test.skip(browserName === 'webkit', WEBKIT_IDB_BLOB_REASON)`
on every test that depends on the IDB+Blob enqueue path. Shared
reason text lives at `tests/e2e/_fixtures/webkitIdbBlobGate.js`
so removing the gate (when Playwright fixes the upstream issue)
is a single-grep operation. R4b adds iOS-real coverage of the
queue+pill surface via `tests/simulator/offline-drain.test.mjs`:
injects a record into the IDB queue directly, navigates to
PhotosView, asserts the sync-pill renders with "1 syncing".
Passes in ~3s against booted iPhone 17 / iOS 26.5.

**Affected specs (all now gated):**
- `photos-offline.spec.js` (both tests — R4 directly)
- `photos-dispatch.spec.js` (the two sync-pill tests — R6)
- `photos-screenshots-m2.spec.js` (sync-pill screenshot — R5)
- `photos-screenshots-m4.spec.js` (sync-pill drain screenshot — R5)

---

## R5 — Two M2/M4 visual-screenshot specs fail on WebKit `[test, S3 → resolved]`

**Status (2026-05-25): [resolved]** — Confirmed downstream of
R4. Both screenshot tests render the sync pill, which depends
on the IDB+Blob enqueue that Playwright's WebKit chokes on.
Gated via the same `WEBKIT_IDB_BLOB_REASON` skip pattern as R4.

---

## R6 — photos-dispatch retry + 500-handling fail on WebKit `[test, S3 → resolved]`

**Status (2026-05-25): [resolved]** — Same downstream-of-R4
finding: both failing tests assert on the sync pill, which
doesn't render because Playwright WebKit's IDB+Blob fails.
Gated via the same `WEBKIT_IDB_BLOB_REASON` skip pattern.

---

## J1 — Journey 01 locator chain `[test+app, S3 → resolved]`

**Status (2026-05-25): [resolved]** — Two fixes:

1. Added `data-testid="threaded-photo-picker"` and
   `data-testid="threaded-photo-save"` to ThreadedMemories.jsx
   (minimal app change — adds inert attrs to existing buttons).
   Journey-01 now uses these testids instead of role+name
   matching.
2. Replaced the final assertion `locator('img').first()` with
   memory-metadata assertions (`/\d+ memory/` text + Delete
   button visibility) — the mocked /assets URL doesn't actually
   serve image bytes, so the `<img>` never renders even after
   the memory saves successfully.

Skipped on webkit-mobile per the R4 IDB+Blob pattern (the save
flow trips `IDBObjectStore.put({...blob})` on Playwright WebKit).

---

## J2 — Journey 03 dispatch-video-input not present `[test, S3 → resolved]`

**Status (2026-05-25): [resolved]** — Skipped on both Playwright
projects. webkit-mobile would otherwise hit the R3a-class
WebCodecs gap; chromium_headless_shell can't decode iPhone .mov
(h.264 in QuickTime container) — HTMLVideoElement reports
videoWidth/videoHeight = 0 and the encode pipeline throws
'video has no dimensions' (verified via diagnostic). Real iOS
Safari decodes .mov fine; iOS-real coverage of this surface
lives in `tests/simulator/video-encode.test.mjs` (R3b).

---

## J3 — Journey 05 share-in description not pre-filled `[test, S4 → resolved]`

**Status (2026-05-25): [resolved]** — Two test fixes needed (the
carryover called out one):

1. Added explicit `import-enrich.click()` after the category
   pick. The mocked `/draft` response only fires on Enrich, not
   on URL paste, so descriptions weren't populated.
2. Added explicit address fill (`27 Holmes St, Mystic, CT`).
   The Google Maps URL parser extracts name + lat/lng but NOT
   address — the visible "5 Water St, Mystic, CT" in the field
   was placeholder text, not a value. readyToSave requires a
   non-empty address, so without this fill the Save button stays
   disabled even when everything else looks populated.

---

## J4 — Journey 07 offline sync-pill missing `[test, S3 → resolved]`

**Status (2026-05-25): [resolved]** — Fix: replaced
mockSuccessfulUpload (which unconditionally returns 200) with a
stateful mock that returns 503 while `simulateOffline=true` and
200 after we flip it on reconnect. The previous mock contradicted
the offline state — even with `context.setOffline(true)`, the
route handler still fired and returned 200, so the upload
succeeded and nothing queued; the sync-pill assertion timed out.
Also added explicit hidden→visible visibility-change toggle on
reconnect (App.jsx's onVisibility only runs on the visible
transition).

Skipped on webkit-mobile per the R4 IDB+Blob pattern.

---

## N1 — Network matrix drop-and-resume not draining `[test, S3 → resolved]`

**Status (2026-05-25): [resolved]** — Pure test bug, no skip
needed on either project. Fix: route registration order.
mockSuccessfulUpload + dropFirstThenResume were both registered
BEFORE setupAlbumComposer ran seedTripIntoCache (which adds a
catch-all 404 route). Playwright's route matching is LIFO, so the
catch-all caught the first /assets/photo call with 404 and
dropFirstThenResume's abort never fired. Status still hit "Saved"
(via queueSilently catching the 404), but `probe.dropped()`
returned false. Reordered: setup first, then mocks.

Note: the original "no auto-retry" hypothesis was correct —
the dispatch flow queues silently on error and shows "Saved" —
but the test isn't asserting on retry behavior; it's just
asserting that the first attempt was actually intercepted.

---

## Triage summary

| Severity | Count | Notes |
|---|---|---|
| S1 (blocking) | 0 | R3 [resolved] — R3a (Playwright skip) + R3b (Simulator journey that uncovered + fixed real iOS bug in videoPipeline/worker) |
| S2 (real bug, important) | 0 | All closed. R1 [resolved] base-Event swipe bypass. R4 [resolved] reclassified to [test] — Playwright WebKit IDB+Blob quirk, real iOS verified clean |
| S3 (smaller real bug or test bug) | 0 | All closed. J1 (data-testids on ThreadedMemories + memory-metadata assertion). J4 (stateful mock replacing mockSuccessfulUpload). N1 (route registration order — setup must register the catch-all BEFORE the more specific mocks since Playwright LIFO). R2, R5, R6 closed via the R4 IDB+Blob skip pattern. J2 closed via skip on both projects (.mov codec gap on chromium + WebCodecs gap on webkit) |
| S4 (cosmetic test bug) | 0 | J3 closed — needed two test fixes (enrich click + address fill) |

**Total bug-pile items:** 11 originally; 11 closed. Bug pile clear.

## What this catches that the prior suite didn't

Before Item A.1 (single Chromium project), every WebKit-only
bug in the table above was invisible. The webkit-mobile project
flipped 14 silent passes into 14 explicit failures on the same
run. That's exactly the "tests pass but Helen's iPhone is
broken" gap the bug trap was designed to close.

## What this still doesn't catch

- WebKit-on-macOS differs from real iOS Safari (memory limits,
  WebCodecs availability, touch event implementation). Item A.6
  closes that gap once the Simulator is set up.
- Real cellular network conditions (BoP at a volleyball arena).
  Bounded real-device verification by Jonathan covers that bucket
  — not for every commit, only for milestone closeouts on
  platform-specific surfaces.
- Hardware-specific iOS Safari memory pressure (the bug that
  prompted this whole punchlist). The structural fix landed in
  commit `21fc084` (saveAsset auto-downscale) + `d80fbed` (photon
  resize on Worker); these protect against recurrence
  structurally even without test coverage of the symptom.

## Proposed fix order (after Group A close + this status pass)

Per user direction: severity-first, [real] before [test] within
a tier. Each fix lands as a separate commit with a regression
test that fails-before / passes-after; WebKit-mobile pass
required; Simulator pass for any upload/camera/etc. surface.

**Tier 1 — S1 [real]:**
1. **R3** — confirm Playwright WebKit's WebCodecs status (likely
   incomplete), gate the encode-pipeline test with `test.skip(...
   webkitWithoutWebCodecs)`, run the same test under the
   Simulator gate to keep iOS-real coverage. **Pure test fix
   once the gating is sound; no app change.**

**Tier 2 — S2 [real]:**
2. **R1** — lightbox touch on webkit. Two possible shapes:
   (a) test fix: swap synthetic TouchEvent for Playwright's
   `page.touchscreen.swipe()` (engine-native dispatch);
   (b) app fix: app's swipe detector needs to handle the
   WebKit-on-macOS event variant. Reproduce on Simulator to
   distinguish. **DESIGN-DECISION POSSIBLE** if the answer is
   (b) — touch detection logic could change UX.
3. **R4** — offline sync-pill on webkit. Same investigate-on-
   Simulator-first sequence. If real on iOS: high-priority real
   bug. If Playwright-WebKit-only: test gating + add Simulator
   coverage. **DESIGN-DECISION POSSIBLE** if the pill
   conditional logic itself needs changes.

**Tier 3 — S3 [real or test], real-leaning first:**
4. **R5, R6** — downstream of R4; resolve in the same commit
   or shortly after.
5. **J4, N1** — both fail on both projects, suggesting
   test-side issues with the offline / drop-and-resume
   assertions. Pure test fixes most likely.

**Tier 3 — S3 [test]:**
6. **R2** — replace in-page dynamic import with a DOM-driven
   assertion path through the real surface (journey-01 already
   covers this surface; merge or extend).
7. **J1** — add data-testids to ThreadedMemories' photo picker
   button + composer rail; update journey to use them.
8. **J2** — add WebCodecs feature-detect skip to journey-03;
   shares R3's resolution.

**Tier 4 — S4 [test]:**
9. **J3** — add the missing `import-enrich` click between
   category select and description assertion. ~5 min.

**Notes that affect the order:**
- Three entries (R4, R5, R6) share a root cause; one fix may
  close all three.
- Three entries (R3, J2 + the R3 test gate) share the WebCodecs
  root cause; one investigation may close all three.
- J1's data-testid additions are a code change to
  ThreadedMemories — small, but a real edit.
- **markdown rendering path is OFF-LIMITS** for this fix series
  per user direction; react-markdown rollback is queued
  separately and any KNOWN_BUGS fix touching ClaudeBubble or
  the marked-derived render must stop and check in first.

Don't start any of these until the user signs off on this
status pass.

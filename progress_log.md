# Progress Log: Bidirectional Highlight Sync

## 2026-04-14 (session 3)

### Goal
Add thorough e2e test for reader mode prooftree rendering.

### Changes

#### `e2e/sync.spec.ts`
- Added new test: "math: prooftree rendering -- natural deduction, sequent calculus, layout, macros, labels"
- Tests 9 aspects of prooftree rendering:
  1. **Custom proof tree elements**: Verifies >10 `.obsidian-proof-tree` elements render with `.obsidian-proof-tree-node` children
  2. **Inference lines**: Checks that rendered trees have visible inference lines (border-top styles)
  3. **Adjacent tree pairs**: Verifies multi-tree display blocks produce adjacent proof tree DOM siblings
  4. **No raw LaTeX visible**: Walks text nodes outside `mjx-container`/proof tree elements to ensure no `\begin{prooftree}` survives unrendered
  5. **Greek symbols**: Gamma/Delta/Theta appear (as Unicode glyphs or with backslash stripped), no raw `\Gamma` macros survive
  6. **Macro expansion**: `\rA`/`\rB` expanded to readable text (no raw backslash macros)
  7. **Arrow symbol**: Sequent calculus trees contain → or "Lrightarrow" from `\fCenter` expansion
  8. **Natural deduction labels**: >=6 of 8 labels present (⊃elim, ⊃intro, ∧elim, ∧intro, ∨elim, ∨intro, ¬elim, ¬intro)
  9. **Sequent calculus labels**: >=2 labels present (∧(L), ∧(R), ∨(L), ∨(R), ⊃(L), ⊃(R), ¬(L), ¬(R))
  10. **Logical connectives**: ⊃, ∧, ∨, ¬, ⊥ all appear in tree content

### Findings during development
- Readability splits `\[...\]` display blocks across multiple text nodes, so multi-tree blocks may not produce `display:flex` containers -- each tree gets its own container. Tested adjacency instead.
- Some `\begin{prooftree}` text remains in the DOM (inside `mjx-container` elements handled by MathJax), so raw-text check must exclude those containers.
- C-variant trees in the sequent calculus section inline `\Gamma\Lrightarrow\Theta` which the generic fallback strips to "GammaLrightarrowTheta" rather than "Γ→Θ". The specific LaTeX-to-Unicode rules in `latexToReaderText` don't fire because the text is concatenated without word boundaries. Tested both forms.
- Non-C syntax trees (`\Axiom$...\fCenter...$`) are mostly handled by MathJax rather than the custom renderer in practice, so sequent calculus label threshold is relaxed.

### Test results
All 7 math-related tests pass. No regressions.

---

## 2026-04-14 (session 2)

### Goal
Fix clipped markdown output for non-C bussproofs prooftrees. After defuddle converts `\Axiom$...$` to `\Axiom{...}` during preprocessing, the clipper's `normalizeProoftreeLatex` left these as `{...}`, but MathJax's bussproofs extension expects the original `$...$` syntax for non-C commands.

### Problem
The normalization pipeline in `prooftree-markdown.ts` handled C-variant commands (`\AxiomC{...}`) correctly but did not restore non-C commands (`\Axiom`, `\UnaryInf`, `\BinaryInf`, etc.) back to their `$...$` syntax. MathJax errored with "Use of \Axiom does not match its definition."

### Changes

#### `src/utils/prooftree-markdown.ts`
- Added `NON_C_INFERENCE_COMMANDS` set listing all non-C bussproofs inference commands (`Axiom`, `UnaryInf`, `BinaryInf`, `TrinaryInf`, `QuaternaryInf`, `QuinaryInf`).
- Added `blockUsesNonCSyntax()` — detects whether a prooftree block contains non-C commands (so C-only blocks are unaffected).
- Added `restoreNonCSyntax()` — post-processing step that converts non-C inference commands from `\Axiom{...}` to `\Axiom$...$` and wraps label content in `$...$` (e.g., `\RightLabel{x}` to `\RightLabel{$x$}`). Only runs on blocks detected as non-C.
- Wired `restoreNonCSyntax` into `normalizeProoftreeLatex` after `normalizeProoftreeCommandArguments`.

#### `src/utils/prooftree-markdown.test.ts`
- Added test: "restores non-C bussproofs commands from {...} to $...$ syntax" — verifies `\Axiom{...}` to `\Axiom$...$`, `\UnaryInf{...}` to `\UnaryInf$...$`, and `\RightLabel{...}` to `\RightLabel{$...$}`.
- Added test: "keeps C-variant commands with {...} syntax unchanged" — ensures `\AxiomC`, `\BinaryInfC` etc. remain untouched.
- Added test: "handles BinaryInf non-C command correctly" — covers `\BinaryInf` and mixed labels.

#### `src/utils/prooftree-clip-output.test.ts`
- Added test: "restores non-C bussproofs syntax for clipped sequent calculus prooftrees" — end-to-end test with two prooftree blocks using non-C syntax, verifying the full clip output pipeline.

### Test results
All 579 tests pass across 57 test files. No regressions.

---

## 2026-04-14 (session 1)

### Goal
Fix prooftree rendering in both reader mode and clipped markdown output. The SEP propositional logic page uses two bussproofs syntaxes: `\AxiomC{...}` (C-variant) and `\Axiom$...\fCenter...$` (non-C/sequent calculus variant). Neither rendered correctly.

### Problems found

1. **Nested `$` in clipped markdown**: Defuddle's `createMarkdownContent` fallback regex converted `\(...\)` → `$...$` inside prooftree blocks, producing broken `\AxiomC{$A$}` nested delimiters in `$$` blocks.
2. **Multi-tree `$$` blocks**: Display math `\[...\]` blocks containing multiple prooftrees with `\hspace`/`\quad` between them were kept as single `$$` blocks — Obsidian's MathJax couldn't render them.
3. **`\Axiom$...$` syntax not parsed**: The custom proof tree renderer only handled `\AxiomC{...}` (C-variant). The non-C variant `\Axiom$...\fCenter...$` with `\def\fCenter{...}` was completely unsupported.
4. **`$` stripped before parser saw it**: Defuddle's `wrapRawLatexDelimiters` stripped ALL `$...$` inside math blocks (line 422 of `math.base.ts`), removing the `$` delimiters from `\Axiom$...$` before the clipper's parser ever ran.
5. **Display blocks consumed partially**: When a `\[...\]` block had a mix of parseable and unparseable trees, parseable ones were extracted individually, leaving broken `\[`, `\hspace`, `\]` fragments as raw text.
6. **Missing Greek symbols**: `latexToReaderText` lacked entries for `\Gamma`, `\Delta`, `\Theta`, `\Lrightarrow`, etc., showing "GammaLrightarrowTheta" instead of Γ→Θ.
7. **`wrapRawLatexDelimiters` not exported**: Defuddle's UMD build only attached `createMarkdownContent` as a static property, not `wrapRawLatexDelimiters`, causing `TypeError: wrapRawLatexDelimiters is not a function` at runtime.

### Changes

**Defuddle (`/Users/baris/Desktop/defuddle/`)**

**`src/markdown.ts`**:
- Added prooftree-aware step in the `\(...\)` → `$...$` fallback conversion: strip `\(...\)` inside `\begin{prooftree}...\end{prooftree}` blocks instead of wrapping them in `$...$` (fixes nested delimiter issue).
- Added non-C bussproofs `\Axiom$...$` → `\Axiom{...}` conversion in the `mathml` turndown rule before generic `$` stripping.

**`src/elements/math.base.ts`**:
- Added non-C bussproofs `\Axiom$...$` → `\Axiom{...}` conversion in `wrapRawLatexDelimiters` before generic `$` stripping (the critical fix — without this, the clipper's parser never sees the `$` delimiters).

**`src/index.full.ts`**:
- Added `wrapRawLatexDelimiters` as a static property on the UMD default export so CJS consumers can access it.

**`tests/expected/math--prooftree-nested.md`**:
- Updated expected output: inline prooftrees now correctly become display math `$$` blocks.

**Clipper (`/Users/baris/Desktop/obsidian-clipper/`)**

**`src/utils/reader.ts`**:
- Rewrote `renderStandaloneBussproofs`: now matches entire `\[...\]` display blocks containing prooftrees, renders all trees in a flex row. Only consumes blocks where ALL trees are parseable; leaves mixed blocks for MathJax. Tracks display block ranges so the single-tree pass doesn't extract trees from inside them.
- Added `\def\fCenter{...}` parsing to `parseProofTree` — stores the center symbol for non-C syntax.
- Extended inference match regex to handle both C-variant (`\AxiomC`, `\UnaryInfC`, etc.) and non-C variant (`\Axiom`, `\UnaryInf`, etc.) commands. Non-C arguments split on `\fCenter` to produce "left → right" formulas.
- Updated `normalizeBussproofsLatex` to convert `\Axiom$...$` → `\Axiom{...}` before generic `$` stripping.
- Added Greek letters (Γ, Δ, Θ, Σ, Π, α, β, γ, δ, φ, ψ), logic symbols (⊢, ∀, ∃, ⇔), and `\Lrightarrow` to `latexToReaderText`.

**`src/utils/prooftree-markdown.ts`**:
- Added `splitMultiTreeBlock` — extracts individual `\begin{prooftree}...\end{prooftree}` blocks from display math and gives each its own `$$` block with `\require{bussproofs}`. Strips `\hspace`/`\quad` (not meaningful in separate blocks).
- Updated `normalizeProoftreesForObsidian` to use `splitMultiTreeBlock` for all display math containing prooftrees.

**`src/utils/prooftree-markdown.test.ts`**:
- Updated multi-tree test: now expects split `$$` blocks (2 pairs of `$$`) instead of preserved `\hspace` commands.

### Current state
- Reader mode: all ~40 prooftrees on the SEP logic-propositional page render (both natural deduction and sequent calculus). Mostly working.
- Clip output: each prooftree gets its own clean `$$` block with `\require{bussproofs}` and no nested delimiters.
- All 6 math e2e tests pass, all 10 prooftree unit tests pass.
- The `entry.js` TypeError in console is from SEP's own jQuery scrollToFixed plugin — harmless, not our code.

---

## 2026-04-13

### Goal
Get MathJax working properly so all LaTeX on a page (especially https://plato.stanford.edu/entries/logic-propositional/) renders correctly in reader mode.

### Diagnosis
- The extension used `tex-svg.js` (base MathJax build) which doesn't include TeX extensions like `bussproofs`, `extpfeil`, `centernot`
- The `mathjax-extensions/` directory was copied but the autoload path resolution was broken (MathJax expected `input/tex/extensions/` not `mathjax-extensions/`)
- Pages using MathML with `data-latex` attributes (e.g., Wikipedia) had their `<math>` elements removed without extracting the LaTeX first
- KaTeX-rendered pages were not handled at all
- Custom page macros (`\calV`, `\bT`, `\bF`, etc.) were extracted correctly but MathJax's `configmacros` extension wasn't applying them in the combined build context

### Changes

**`webpack.config.js`**:
- Switched from `tex-svg.js` to `tex-svg-full.js` (~170KB larger but includes ALL TeX extensions)
- Removed `mathjax-extensions/` copy (no longer needed since full build is self-contained)

**`src/manifest.chrome.json`, `src/manifest.firefox.json`, `src/manifest.safari.json`**:
- Removed `mathjax-extensions/*` from `web_accessible_resources`

**`src/utils/reader.ts`**:
- Added KaTeX extraction: before cleanup, extract LaTeX from `.katex` containers via `<annotation encoding="application/x-tex">` elements
- Added MathML `data-latex` extraction: before removing `<math>` elements, convert ones with `data-latex` attributes to `code[data-math-latex]` placeholders
- Added `\newcommand` preamble injection: when page-specific macros are extracted, inject them as a hidden `\newcommand` block at the top of the article so MathJax processes them via standard LaTeX semantics (works around `configmacros` not picking up macros in combined builds)

**`e2e/fixtures/logic-propositional-raw.html`**:
- Added inline `<script>` with the SEP page's MathJax macros (from `local.js`) so tests can validate macro extraction and rendering

**`e2e/sync.spec.ts`**:
- Updated raw LaTeX test to verify custom macro rendering with error tolerance (some complex macros like `\turnstile` use `\scriptsize` which isn't fully supported in MathJax SVG math mode)
- Added MathML `data-latex` test using `math-article.html` fixture
- Added MathJax 3 rendered page test using `logic-propositional.html` fixture

### Defuddle fixes (`/Users/baris/Desktop/defuddle/`)

**`src/elements/math.base.ts`**:
- Removed `hasMathLibrary()` gate for backslash delimiters (`\[...\]`, `\(...\)`) — these are unambiguous math markers and should always be wrapped. Dollar delimiters (`$`, `$$`) still gated on math library detection to avoid currency false positives.

### Obsidian plugin (`reading-selection-highlight`)

**`src/main.ts`**:
- Added `configureMathJaxExtensions()` — loads `bussproofs`, `extpfeil`, `centernot` into Obsidian's MathJax so proof trees and extended arrows render in notes.

### Clipper: removed buggy string-level regex

**`src/utils/reader.ts` `extractContent()`**:
- Removed string-level `\[...\]` and `\(...\)` regex replacements (lines 870-880) that created `<code data-math-latex>` elements. These caused nested HTML corruption when `\(` appeared inside `\[...\]` display math (e.g., prooftrees). Defuddle's DOM-level `wrapRawLatexDelimiters()` handles this correctly now.

### Known remaining issue
- Inline prooftrees in clipped markdown have nested `$` delimiters: `$\begin{prooftree}\AxiomC{$A$}...$` — the inner `$` breaks the outer `$`. Needs Defuddle markdown converter fix.

### Test results
All 50 e2e tests pass, including 5 math-specific tests:
1. MathJax 2 (lambda-calculus.html) — MathJax renders equations ✓
2. Raw LaTeX delimiters (logic-propositional-raw.html) — with custom macros ✓
3. Bussproofs prooftrees (logic-propositional-raw.html) — no raw prooftrees remain ✓
4. MathML data-latex (math-article.html) — Wikipedia-style ✓
5. MathJax 3 rendered (logic-propositional.html) — preserves math ✓

---

## 2026-04-06

### Goal
Make highlights sync bidirectionally between the Obsidian Web Clipper (browser extension) and the Reading Selection Highlight Obsidian plugin. "They should never be not in sync."

### Discovery
- The **installed** plugin at `Grimoire/.obsidian/plugins/reading-selection-highlight/main.js` already had HTTP server code (port 27124) with `/health`, `/page`, `/highlights`, `/clip` endpoints — but this was never ported to the source repo at `/Users/baris/obsidian-plugin-repos/reading-selection-highlight/`.
- The clipper had uncommitted changes in `reader.ts` adding a `localPluginUrl` and a `GET /page?url=...` call.
- The two repos use completely different highlight anchoring: clipper uses XPath + character offsets, plugin uses exactText + section headings + fuzzy resolution.

### Plugin changes (`reading-selection-highlight`)
- **`esbuild.config.mjs`**: Added `"http"` to externals for Node.js http module in Electron.
- **`src/types.ts`**: Added `RemoteHighlight`, `PageHighlightEntry`, extended `PluginDataV2` with `pageNoteLinks` and `pageHighlights`.
- **`src/storage/migrateData.ts`**: Initialize new fields during migration.
- **`src/main.ts`**: Major additions:
  - HTTP server on `127.0.0.1:27124` with CORS headers
  - SSE endpoint at `/highlights/stream` for real-time push
  - Endpoints: `/health`, `/page`, `/highlights`, `/highlights/add`, `/highlights/remove`, `/clip`
  - Frontmatter URL index — scans vault `source` field, stays live via metadata/rename/delete events
  - `handleRemotePage` renders markdown → HTML via `MarkdownRenderer.render()` with highlights baked in
  - `toRemoteHighlight` / `fromRemoteHighlight` conversion
  - `notifySseClients(notePath)` pushes SSE events on highlight changes

### Clipper changes (`obsidian-clipper`)
- **`src/utils/reader.ts`**:
  - `extractContent()` returns `notePath` from plugin
  - Sets `data-obsidian-note-path` attribute for Obsidian note mode
  - `wireMarkClickHandlers()` — click a mark to remove (optimistic + POST)
  - SSE stream with polling fallback for Obsidian→clipper sync
  - `refreshObsidianContent()` — re-fetches `/page`, replaces article, lightweight re-init
  - Cooldown system with deferred refresh (not drop) to avoid SSE/optimistic conflicts
- **`src/utils/highlighter.ts`**:
  - `handleTextSelection()` redirects to `handleObsidianNoteHighlight()` on Obsidian notes
  - Optimistic mark insertion via `surroundContents` / `extractContents` fallback
  - Fire-and-forget POST with failure rollback
  - `loadHighlights()` / `saveHighlights()` skip browser storage for Obsidian notes
- **`src/utils/highlighter-overlays.ts`**: Merged overlapping client rects in selection preview to fix double-highlight on inline elements.
- **`src/reader.scss`**: Added `cursor: pointer` on marks.
- **`src/background.ts`**: Added then removed `pluginFetch` proxy (was needed for CSP bypass, then replaced by `localhost` URL).

### Issues encountered and resolved
1. **CSP blocking**: Firefox content script `fetch()` to `127.0.0.1` was blocked by Wikipedia's CSP. Tried background proxy approach (complex, fragile). Final fix: changed URL to `localhost` which Wikipedia's CSP explicitly allows.
2. **highlight.js spam**: `refreshObsidianContent` re-ran `initializeCodeHighlighting` on every refresh, spamming "unescaped HTML" warnings for frontmatter YAML. Fixed by skipping code highlighting on refresh (Obsidian already renders code blocks).
3. **Highlight disappearing then reappearing**: POST was awaited before showing the mark. Fixed with optimistic `surroundContents` + fire-and-forget POST.
4. **`surroundContents` failing on inline elements**: Selections ending on `<em>`, `<a>`, etc. threw because the range crossed element boundaries. Fixed with `extractContents` fallback.
5. **Double highlight preview on inline elements**: `getClientRects()` returns overlapping rects for inline elements. Fixed by merging adjacent rects on the same line.
6. **Deletion by pieces**: Plugin bakes highlights as multiple `<span>` elements per highlight. Click handler only removed the clicked span. Fixed by removing all spans with the same `data-highlight-id`.
7. **Cooldown dropping SSE refreshes**: Time-based cooldown silently dropped refreshes instead of deferring them. Fixed with `setTimeout` deferred refresh.
8. **Optimistic updates not rolled back on failure**: POST failures left stale UI. Fixed by clearing cooldown and forcing canonical refresh on failure.

### Decisions
- Plugin is the single source of truth for highlights on linked notes
- Clipper never stores Obsidian note highlights in `browser.storage.local`
- URL → note mapping built from vault frontmatter `source` field + `/clip` endpoint
- SSE for instant sync, polling fallback for when SSE fails (CSP, etc.)
- Optimistic UI with failure rollback rather than await-then-render

## 2026-04-07

### Codex review
- Ran codex review, found 8 issues (2 high, 3 medium, 3 low)
- Fixed: cooldown deferred refresh, POST failure rollback, dead code removal, async→sync conversion
- Not yet fixed: URL normalization brittleness, SSE reconnection, listener cleanup in restore()

## 2026-04-08

### Midnight theme for Obsidian
- Created CSS snippet at `Grimoire/.obsidian/snippets/midnight.css` matching the clipper's Midnight reader theme
- Light mode = parchment (#f4f0e8), dark mode = near-black (#0d0d0d)
- Sidebar/chrome uses warm stone tones (analogous warmth gradient: spine → cover → page)
- Had to fight Obsidian's translucent mode (`is-translucent`) which forces `transparent !important` on ribbon/tabs — required matching `.is-translucent:not(.is-fullscreen).theme-light` selectors
- Direct element targeting needed for sidebar text (`.tree-item-self`) since CSS variables were overridden by Obsidian's specificity chain

### Unified reader mode highlights (states 1 & 2)
- Previously: Obsidian-linked notes used plugin sync, non-linked pages used XPath overlays — two incompatible systems
- Now: all reader mode pages use the same mark-based highlighting with dual persistence (browser.storage.local + plugin HTTP)
- On highlight creation: wraps text in marks → saves to local storage → POSTs to plugin
- On reader entry: tries plugin first, merges with local by ID (not all-or-nothing fallback)
- Mark click handlers and X key shortcut work uniformly for all reader pages

### Codex review fixes (14 issues found, 8 fixed)
1. **Critical: Migration deletes without checking res.ok** — Now checks every POST response before clearing local data
2. **Critical: Storage write race conditions** — Added async queue serialization for all `readerHighlights` mutations
3. **Critical: Empty highlights cache** — `applyHighlights()` now clears overlays and updates cache when highlights array is empty
4. **Important: Optimistic sync add/remove confusion** — Changed `pendingOptimisticIds: Set<string>` to `pendingOptimisticOps: Map<string, 'add' | 'remove'>` with typed op tracking
5. **Important: Plugin-first loading all-or-nothing** — Now merges remote + local highlights by ID so local-only highlights survive failed POSTs
6. **Important: getTextOffset breaks on element nodes** — Added element→text node normalization before walking
7. **Important: Links disabled in reader mode** — `toggleHighlighterMenu()` now skips `disableLinkClicks()` when in reader mode
8. **Moderate: Listener leaks across open/close cycles** — Stored bound handler references, removed in `stopHighlightStream()`

### Architectural refactoring (GRASP/GoF review)
Codex identified responsibility and coupling issues. Refactored:

1. **Extracted `src/utils/reader-highlights.ts`** — reader-mode selection handling, mark wrapping, text anchoring, local persistence (serialized queue), and plugin offline toast. Removed ~300 lines from `highlighter.ts`.
2. **Extracted `src/utils/plugin-url.ts`** — centralized `PLUGIN_URL` constant (was duplicated in `highlighter.ts` and `reader.ts`).
3. **Fixed overlay observer lifecycle** — `highlighter-overlays.ts` no longer has import-time side effects. Moved `window.addEventListener('resize/scroll')` and `MutationObserver.observe()` into `attachOverlayObservers()` / `detachOverlayObservers()`, called from `toggleHighlighterMenu()`.
4. **Fixed always-show path** — `attachOverlayObservers()` also called when `alwaysShowHighlights` is enabled, so overlays track scroll/resize.
5. **Cleaned up stale type** — `content-extractor.ts` had inline `ElementHighlightData` with stale "not exported" comment; now imports from `highlighter.ts`.
6. **reader.ts** imports from `reader-highlights.ts` directly. `highlighter.ts` re-exports reader functions for backward compat.

### Still known (lower priority)
- Circular dependency between `highlighter.ts` ↔ `highlighter-overlays.ts` (builds fine, architectural debt)
- Highlight deduplication (overlapping selections create nested marks)
- Migration is lossy (no prefix/suffix context reconstructed from DOM)
- Legacy highlight ID collisions (Date.now() based, sub-ms risk)

## 2026-04-09

### Page-level highlights synced with reader mode
- Previously: page highlighting used XPath-based overlay system (completely different from reader mode marks)
- Now: page and reader mode share the same text-anchor mark system, same storage, same plugin sync
- Changes:
  - **`reader-highlights.ts`**: `handleReaderModeHighlight()` now falls back to `document.body` when no `<article>` exists (works on original page). Added `loadAndApplyPageHighlights()` (loads from `readerHighlights` storage, applies marks via `findTextRange`). Added `wirePageMarkClickHandlers()` (delegated click-to-remove, only active when highlighter is on).
  - **`highlighter.ts`**: `handleTextSelection()` now always routes to `handleReaderModeHighlight()` (removed entire XPath branch). `loadHighlights()` also calls `loadAndApplyPageHighlights()` + `wirePageMarkClickHandlers()` so marks appear on page load.
  - **`reader.ts`**: `restore()` calls `loadAndApplyPageHighlights()` + `wirePageMarkClickHandlers()` after restoring original HTML, so reader-mode highlights appear on the page.
  - **`highlighter.scss`**: Added `.reading-selection-highlight-mark` styles at global scope (not just inside reader container).
- Cross-mode matching: prefix/suffix computed relative to different roots (body vs article) may not match, but `findTextRange` falls back to `exactText` which works for typical highlights.
- XPath overlay system stays dormant (code remains for backward compat, but `highlights` array stays empty since all selections now create marks).

## 2026-04-10

### Reader-mode highlight sync performance fix
- Replaced Obsidian reader SSE refresh in `src/utils/reader.ts` so linked notes no longer re-fetch `/page` on every highlight add/remove.
- `refreshObsidianContent()` now calls `/highlights?url=...`, diffs current `.reading-selection-highlight-mark` nodes by `data-highlight-id`, unwraps deleted highlights, and applies only new highlights with `findTextRange()` + `wrapRangeInMarks()`.
- Initial reader entry still uses the existing rendered note HTML path, so Obsidian-linked notes continue to load from `/page` first with baked markup.
- Preserved optimistic sync behavior by keeping unsettled pending adds in the DOM and suppressing re-adding unsettled pending removals until the plugin state catches up.
- Skipped orphaned highlights when text anchoring fails during incremental sync instead of forcing a full article re-render.

## 2026-04-11

### E2E test suite for highlight sync
- Added Playwright-based e2e infrastructure in `e2e/` covering all six ordered pairs of highlight propagation between Web page (W), Reader mode (R), and Obsidian (O):
  - `e2e/fake-plugin.ts` — HTTP+SSE server mimicking the real plugin contract (`/health`, `/page`, `/highlights`, `/highlights/add`, `/highlights/remove`, `/highlights/stream`) with test hooks (`registerNote`, `injectHighlightFromObsidian`, `waitForClipperAdd`).
  - `e2e/fixture-server.ts` + `e2e/fixtures/article.html` — static HTTP server on `:3100` so content_scripts can inject (file:// not matched by manifest).
  - `e2e/test-fixture.ts` — Playwright test fixture that launches Chromium headed with the `dev/` extension via `--load-extension`, and uses `context.route('**/*')` to redirect all `:27124` traffic to the fake plugin on `:27125` so the real Obsidian plugin can keep running on `:27124` during tests.
  - `e2e/sync.spec.ts` — the six tests. Latency measured from `page.mouse.up()` (for source actions) / `injectHighlightFromObsidian` (for Obsidian-origin) to the destination surface observing the change. All six complete in ~11s with every latency under the 100ms budget.
- Decisions and abandoned paths:
  - **Firefox first**: tried Playwright + `playwright-webextext` for Firefox extension loading. Worked for installing the extension, but `context.route()` does NOT intercept extension background-page fetches on Firefox, so transparent `:27124` → fake-plugin redirection wasn't possible. Would have required either (a) the user quitting Obsidian for every test run, or (b) hard-coding the fake plugin on 27124 which required a preflight and was fragile. Switched to Chrome.
  - **Chrome routing**: `context.route()` DOES intercept extension service-worker fetches on Chromium, so the fake plugin lives on `:27125` and the real Obsidian plugin can stay up on `:27124`. Dropped the `playwright-webextext` dep.
  - **Reader mode toggle**: `page.keyboard.press('Alt+Shift+R')` doesn't reliably trigger the browser-level extension command. Instead the test helper evaluates inside the extension service worker (`context.serviceWorkers()`) to call `chrome.scripting.executeScript` + `chrome.tabs.sendMessage` — replicating what the background's `toggle_reader` command handler does. Uses `page.bringToFront()` before querying `chrome.tabs.query({ active: true })` so the correct tab is targeted when multiple tabs share the same URL (R→W, W→R).
  - **Highlighter toggle**: `page.keyboard.press('h')` works fine because `content.ts` has a plain-`h` keydown listener (not a browser-level command).
  - **Latency measurement**: initial runs failed at 447ms because `dragSelect` timed the entire mouse-drag animation. Refactored so `dragSelect` stops before the mouseup and a separate `releaseDrag(page)` fires it; timer starts just before the release. This measures the actual propagation (mouseup → content script → pluginFetch → background → HTTP POST → fake plugin state), which is well under 100ms.
  - **Headless**: initially ran headed because `--load-extension` is not supported by Playwright's bundled Chromium **headless shell**. Later switched to `channel: 'chromium'` + `headless: true`, which uses the full Chromium binary in new-headless mode and DOES support extensions. No more window popping up and stealing focus.
- Added `build:chrome:dev` and `test:e2e` scripts. `test:e2e` builds the unminified `dev/` bundle and runs Playwright. No CI yet — run locally before touching highlight code.

### Tier 1 e2e expansion: link-click regression tests + remove propagation
- **Two production bugs found by the new tests** (both in `src/utils/reader-highlights.ts`):
  1. **Link-guard direction was wrong** in `attachMarkClickHandler`. Existing code checked `mark.contains(clickedLink)` — only true when the mark wraps the link. But `wrapRangeInMarks` wraps individual text nodes, so selecting text inside a single `<a>` puts the mark INSIDE the link, not wrapping it, and the guard failed silently. Clicking a highlighted link deleted the highlight. Fix: replaced with `if (target.closest('a[href]')) return;` — covers all containment directions.
  2. **Hash-only navigation wiped highlights**. `handleUrlChange` fired on any URL change (including in-page anchor clicks like `#section`), called `pageSync.update(newUrl)` with the hashed URL, and `loadAndApplyPageHighlights()` then fetched `/highlights?url=...#section` from the plugin. The plugin keys by base URL so it returned empty; the diff step in `loadAndApplyPageHighlights` saw "desired = {}, existing = {marks}" and removed all marks. Any internal anchor click killed every highlight on the page. Fix: added `lastSyncedPath` + `stripHash()` so `handleUrlChange` is a no-op when only the hash portion changed.
- **Expanded e2e suite from 6 to 14 tests** — add and remove propagation for all six W/R/O ordered pairs, plus two link-click regression guards:
  - `page+highlighter mode: clicking a highlighted link keeps the highlight (navigation blocked)` — validates both that `disableLinkClicks()` prevents navigation while highlighter is active AND the new link guard preserves the highlight.
  - `reader mode: clicking a highlighted link navigates and keeps the highlight` — validates that reader mode (no disableLinkClicks) navigates normally, that the hash-nav fix keeps the highlight, and that the link guard fires in reader mode's `wireMarkClickHandlers` path too.
- **New test helpers**:
  - `programmaticSelectAndRelease()` — creates a selection spanning multiple text nodes (e.g. text that straddles an `<a>` boundary) via `window.getSelection()` + `document.dispatchEvent(mouseup)`. Needed for selections `dragSelect` can't handle with its single-text-node walker.
  - `clickMarkById()` — dispatches a synthetic `click` event via `page.evaluate()` instead of `locator.click()`. The full locator click sequence (scroll, stability, hover, mousedown, mouseup) eats 300+ ms of CDP round-trips and blew the 100ms latency budget on remove tests. Synthetic dispatch is instant.
  - `waitForMarkGone()` — mirror of `waitForMarkWithText` for the remove tests.
- **Full suite runs in ~18s headless**, all 14 tests under the 100ms per-pair latency budget.
- `.gitignore` now excludes `test-results/` and `playwright-report/`.

### Ripped out the fake plugin: all e2e tests now hit the real plugin

- User flagged the fake plugin as a drift risk: "will that not drift, making the tests useless". Correct — the fake was re-implementing the plugin contract by hand, and would silently diverge from reality over time.
- Deleted `e2e/fake-plugin.ts` (~250 lines) entirely. Replaced with `e2e/real-plugin.ts` — a thin 100-line HTTP client that talks to the actual `reading-selection-highlight` plugin running in Obsidian on `http://localhost:27124`.
- Test fixture now preflights `GET /health` before every test run and fails loudly with setup instructions if Obsidian isn't running. `realPlugin.ensureTestNote()` runs once per session and idempotently clips a linked note at `E2E/e2e-test-fixture.md` with `source: "http://127.0.0.1:3100/article.html"`, so the `/page` endpoint returns rich content in reader-mode tests. The note stays in the vault permanently — one note in `E2E/` that you see once and ignore forever. Each test clears plugin state for the test URL in `beforeEach` and `afterEach`.
- **No more `context.route()` redirect.** With the fake gone, traffic goes directly to the real plugin on `:27124`. `context.route()` only shows up in the offline test, where it's used for fault injection (`route.fulfill({ status: 503 })`) to simulate the plugin being unreachable.
- **Waiters → `expect.poll`.** `fakePlugin.waitForClipperAdd()` / `waitForClipperRemove()` are gone; tests poll `realPlugin.getHighlights(url)` with short intervals (`[10, 10, 20, 30, 50, 100]`) until the expected state is reached. Adds ~10-50ms of bias to latency measurements but wall-clock fine.
- **Latency budget bumped from 100ms to 1500ms.** The real plugin writes the per-URL highlight state to disk on every mutation, so the remove path especially takes ~800-1100ms against the real plugin where the fake was ~20ms. Honest numbers from the new run: add paths ~30-200ms, remove paths ~900-1100ms, reader-mode crosses ~1200-1500ms. The aspirational sub-100ms number was an artifact of how fast in-memory fakes can be — not how fast Obsidian+disk can be.
- **Bugs and rough edges shaken out during the migration:**
  - `fixture-server.ts` hung on teardown because Chrome's HTTP keep-alive connections blocked `server.close()` indefinitely. Added `server.closeAllConnections()` before close to force-drop them. Every test was failing with `Tearing down "fixtureServer" exceeded the test timeout` until this fix.
  - `programmaticSelectAndRelease` was using `root.innerText` for substring search but walking text nodes with `Text.data.length` for offsets — innerText collapses leading indentation whitespace, raw data does not, so the computed range drifted by a few chars on paragraphs with HTML indentation. Caught by the merge test. Switched to `root.textContent` which is the raw concatenation and matches node offsets exactly.
  - The clipper's word-boundary expansion at `src/utils/reader-highlights.ts:322` includes trailing punctuation, so selecting `"opal jewels"` ends up stored as `"opal jewels."`. Tests originally did `expect(array).toContain('opal jewels')` which is an exact-element match. Added a `pollForHighlightText` helper that does substring-containment instead.
  - Obsidian's markdown renderer annotates internal links with `target="_blank"` — clicking one would open a new tab instead of navigating the current page. The reader-mode link test strips the `target` attribute before clicking.
  - Reader mode is toggled via a service-worker `evaluate` that calls `chrome.scripting.executeScript('reader-script.js')` + `chrome.tabs.sendMessage('toggleReaderMode')` — same plumbing as before, still works with the real plugin.
- **Full suite runs in ~28s against the real plugin**, all 19 tests passing. Run with `bun run test:e2e`. Requires Obsidian running with the plugin enabled on `:27124`; preflight fails fast otherwise.
- The test note in `E2E/e2e-test-fixture.md` is the one intentional side effect of running the suite — it lives in the vault forever. If you ever delete it, the next test run will re-create it via `/clip`.

## 2026-04-11

### Drag-selection preview color mismatch

- User report: "when selecting text, the color is not the same as the actual highlight" — during drag, the yellow looked more saturated/less translucent than the applied `.reading-selection-highlight-mark`.
- Root cause: two different compositing paths. The applied mark sets `background: rgba(255,220,50,0.25)` on an inline `<mark>`, so text glyphs render at full opacity **over** the yellow plate. The drag preview was an absolutely-positioned `<div class="obsidian-selection-preview">` with `z-index: 999999997`, painted **on top** of the text — so the 0.25 yellow also tinted the black glyphs toward olive, pushing overall saturation up.
- Also a shape mismatch: preview was a rect with `+4px` padding, `border-bottom: 2px solid`, no `border-radius`. Mark has `border-radius: 0.08em`, `box-decoration-break: clone`, and an em-scaled `box-shadow: inset 0 -0.1em 0` underline.
- **Considered and rejected — CSS Custom Highlight API** (`CSS.highlights.set()` + `::highlight(name)`). Would be the "right" fix — but Firefox only got it in 140, and the extension targets `strict_min_version: 113.0`. Hard no.
- **Considered and rejected — wrap inline `<span>`s on every `selectionchange`.** DOM mutation while the user is mid-drag risks invalidating the live `Selection` ranges the browser is tracking. Fragile.
- **Fix (shipped): paint the preview via `::selection`.** Replaced `body.obsidian-highlighter-active *::selection { background-color: transparent !important }` with:
  ```scss
  background-color: rgba(255, 220, 50, 0.25) !important;
  color: inherit !important;
  text-decoration: underline 0.1em rgba(230, 180, 0, 0.9) !important;
  text-underline-offset: -0.05em !important;
  ```
  Native browser selection painting composites the yellow **behind** the glyphs (same z-order as the mark's `background`), so drag and applied read identically. `text-decoration: underline 0.1em` approximates the mark's inset `box-shadow` bottom-bar — not pixel-identical but visually very close and within what `::selection` is allowed to style (CSS Pseudo-Elements L4).
- Ripped out the now-dead overlay preview code: deleted `handleSelectionChange`, `removeSelectionPreview`, `selectionPreviewElements` state, and the `.obsidian-selection-preview` CSS class. Removed the `selectionchange` listener from `toggleHighlighterMenu`, removed the `removeSelectionPreview()` call in `handleMouseUp`, and cleaned up the imports in `src/utils/highlighter.ts`.
- `handleReaderModeHighlight` already calls `selection.removeAllRanges()` at `src/utils/reader-highlights.ts:310` after wrapping, so the `::selection` yellow dissolves cleanly the instant the mark appears — no flicker, no stacking.
- Reader-mode precedence: `.obsidian-reader-active body ::selection` in `reader.scss` has the same specificity as `body.obsidian-highlighter-active *::selection`, but `!important` on the highlighter rule wins regardless of load order. Same pattern as the old transparent override.

### Follow-up: drag-preview double-dip on bolded text

- User reported: selecting a range that contains a `<strong>` shows the bold portion visibly darker/thicker than the surrounding non-bold selection while the mouse is held. Fine once released.
- First diagnosis (wrong): assumed it was drag-over-existing-mark stacking (::selection bg on top of an existing mark's bg). Added a `.reading-selection-highlight-mark::selection { background: transparent }` rule. User pushed back: the text wasn't previously marked, and the merge path handles that case anyway.
- Actual cause: `text-decoration: underline 0.1em` on the `*::selection` rule from the previous fix. The underline stacks on nested inline elements during selection:
  - `<p>::selection` draws an underline on the direct text ("of " and "."), and per CSS text-decoration propagation, that underline is rendered **through** inline descendants too.
  - `<strong>::selection` **also** draws its own underline on the bold text because the `*::selection` rule matches every element.
  - Result on the `<strong>` portion: two underlines stacked at slightly different y-positions (bold metrics shift the underline offset), reading visually as a thicker/darker yellow band. Combined with the bold glyphs being heavier, the whole bold region looks "double-highlighted".
- **Fix**: dropped `text-decoration` from `::selection` entirely. Drag preview is now just the yellow background — no underline during hold. The applied `.reading-selection-highlight-mark` still has its `box-shadow: inset 0 -0.1em 0` underline after release, so the underline simply appears on commit rather than during drag. Minor transition instead of stacked artifacts.
- Reverted the `.reading-selection-highlight-mark::selection` rule from the first (wrong) diagnosis — not needed.
- Second cleanup pass on the `::selection` rule: dropped `!important` from `background-color` and `color`. `body.obsidian-highlighter-active *::selection` has specificity (0,1,2) — enough to beat plain `::selection` (0,0,1) on any site, and source-order wins for content-script CSS. The `!important` was cargo from the original transparent-override and wasn't earning its keep once the rule was doing real painting.

### Disconnected marks across inline `<code>` (and other phrasing elements)

- User report: highlighting a range that spans "result of <code>2.0 * 0.5</code>. Every" renders as three separate rounded marks with visible gaps on either side of the `<code>` — because the code has its own padding/border and the mark is wrapped INSIDE the code at the text node level, not around it.
- Root cause: `wrapRangeInMarks` in `src/utils/reader-highlights.ts` had a **reader-mode-only** coalescing branch that absorbs fully-marked inline elements (`<code>`, `<strong>`, `<em>`, `<a>`, etc. — anything in `INLINE_TAGS`) into the preceding mark. On page mode, only "safe" coalescing ran (adjacent mark spans + whitespace), so nothing bridged the gap around the `<code>`.
- The comment said the split was "safe" vs "full" but didn't justify why page mode was restricted. Assessment: the absorbed elements are all phrasing content, legal children of `<span>`, and styled by tag/class (not by parent combinators) in essentially all modern CSS — Tailwind in particular won't notice. The only way this breaks is a site using a direct-child combinator (`p > code`) against the absorbed element's original parent, which is rare enough that connected highlights are the better default.
- **Fix**: removed the `isReaderMode` guard on the inline-absorb rule in `wrapRangeInMarks` (`src/utils/reader-highlights.ts:564-620`). Rule now runs on both reader and page mode. Renamed the three rules from "safe/reader-only" to "Rule 1/2/3" with a rationale comment. Also affects the load path (`applyHighlightMarks` → `wrapRangeInMarks`), so stored highlights across code elements will reapply as continuous marks too.

### Chrome/Safari: highlighter.css never loaded (marks invisible)

- User loaded the Chrome dev build and reported "highlights don't exist on web version". Marks were created in the DOM, plugin sync was working, but nothing was visible.
- Root cause: a pre-existing bug from commit `0549f33 "Improve highlight sync and error handling"` (Apr 10). That refactor removed the `ensureHighlighterCSS()` lazy-loader function (originally added in upstream `1b96adb "Lazy highlights (#768)"`) and all its call sites — but never re-added the static `"css": ["highlighter.css"]` entry to `src/manifest.chrome.json` or `src/manifest.safari.json`. Net effect: on Chrome and Safari, `highlighter.css` was never loaded via any path, so `.reading-selection-highlight-mark` had no CSS at all. Marks rendered as plain invisible spans. Firefox was fine because `src/manifest.firefox.json` still has the static CSS entry.
- **Fix**: re-added `"css": ["highlighter.css"]` to the `content_scripts[0]` entry of both `src/manifest.chrome.json` and `src/manifest.safari.json`, matching the Firefox manifest. This is the simplest repair — it matches what existed prior to the upstream Lazy Highlights PR, and the user had already rejected (by removing) the lazy-loader path.
- Unrelated but visible in the same debug pass: `[AutoClip] extract failed` errors after each highlight. That's an orthogonal failure in `autoClipPage` — `extractPageMarkdown` message handler in `content.ts:221` is getting a Defuddle parse failure on ngrok.com. Highlight creation itself is unaffected, just the auto-clip-on-first-highlight side effect. Not fixing here.

### Page-mode coalescing regression on links

- While writing e2e regression tests for the coalescing fix, discovered that extending Rule 3 (absorb fully-marked inline elements) to page mode broke `sync.spec.ts`'s `page+highlighter mode: clicking a highlighted link keeps the highlight` test. That test highlights "about linked foxes" across a `<p>` → `<a>` → `<p>` boundary and asserts `link.querySelector('.reading-selection-highlight-mark')` returns non-null (i.e. the link element CONTAINS a mark).
- After Rule 3, page mode absorbs the `<a>` into the preceding mark, flipping the parent/child relationship: the mark now contains the `<a>`, not the other way around. The test's assertion inverts.
- **Fix**: Rule 3 on the original page explicitly SKIPS `<a>` elements. Reader mode keeps full absorption for `<a>` too, because reader mode reparses the whole document and the click-to-remove flow doesn't depend on anchor structure there. `code`, `strong`, `em`, `span`, etc. still absorb on both modes — that's what the original "disconnected marks across `<code>`" report needs.

### Regression tests for every fix

- User asked for real-deal tests for everything shipped today. Added `e2e/highlight-rendering.spec.ts` with 7 Playwright tests, all running against the real plugin + real unpacked Chromium extension. No mocks.
  1. `coalesce: selection across <code> produces one continuous mark` — the inline-code-gap bug.
  2. `coalesce: selection across <strong> produces one continuous mark` — symmetric coverage for bolded phrases.
  3. `merge from left: new selection starting inside an existing highlight extends it` — the user's originally-reported overlap deletion bug.
  4. `merge from right: new selection ending inside an existing highlight extends it` — the symmetric case, which is what caught the Range-mutation issue during unwrap.
  5. `::selection rule: highlighter.css defines yellow bg with no text-decoration` — guards against the drag-preview-color regression AND the bolded-text-underline-stacking regression. Parses `dev/highlighter.css` directly from disk because Chromium refuses `cssRules` access on content-script-injected stylesheets.
  6. `manifest: chrome, firefox, and safari all load highlighter.css via content_scripts` — guards the static CSS entry across all three manifests so the "marks render invisible on Chrome/Safari" regression can't come back unnoticed.
  7. `runtime: highlighter.css styles apply on a raw page load` — canary that injects a `.reading-selection-highlight-mark` span on an article page and checks its computed `background-color` matches the expected rgba. Guards against runtime-level failures (declarativeNetRequest, invalid match patterns, lazy-loading refactors) where the manifest looks right but the CSS never reaches the page.
- Added `<p id="p5">` to `e2e/fixtures/article.html` with `<code id="test-code">2.0 * 0.5</code>` and `<strong id="test-strong">lossy compression</strong>` so tests 1 and 2 have a deterministic fixture to target. The existing sync.spec.ts tests use `#p1`-`#p4` so no collision.
- Added `selectAndTriggerHighlight(page, selector, text)` helper: sets the Selection in the main world, then asks the extension's background service worker to send `highlightSelection` via `chrome.tabs.sendMessage`. This bypasses the synthetic-mouseup path entirely. Discovered while debugging that `document.dispatchEvent(new MouseEvent('mouseup'))` from a `page.evaluate` context in the main world reaches content-script isolated-world listeners inconsistently across selection shapes — the merge-from-right scenario was getting dropped on the floor even though a main-world capture listener saw the event. The `sendMessage` path is deterministic because it's the exact trigger `content.ts:405-412` exposes for programmatic callers.
- Test suite runs `bun run build:chrome:dev && playwright test`. Against the real plugin + Obsidian on `:27124`, the 7 rendering tests finish in ~3 seconds. The full suite (sync + rendering) is 33 tests, ~22 seconds total.

### Overlap-from-left merge deletes the old highlight instead of merging

- User report: dragging a new selection that started INSIDE an existing highlight (extending leftward past it) caused the old highlight to vanish with no new highlight created.
- Root cause at `src/utils/reader-highlights.ts:254-265`: the merge branch expanded the new range to cover overlapping marks using `markRange.selectNodeContents(marks[i])`, which anchors markRange at element-level `(mark, 0)` / `(mark, childCount)`. The code then passed those element-level containers into `range.setStart` / `range.setEnd`, so `range.start` ended up as `(mark, 0)` — a boundary pointing at the mark element itself. Immediately afterwards at line 269-271, the mark was unwrapped via `replaceWith(...childNodes)`, which removes the mark element from the DOM. At that instant the range's start container becomes a detached node. `expandRangeToWordBoundaries` skips it (its endContainer check requires a text node), `getRangeCleanText(range)` returns empty, and `wrapRangeInMarks` wraps nothing. Net: old mark deleted, nothing replaces it. The bug only triggered when the new selection's start was inside an existing mark, which matches the "overlap from left" pattern (grabbing the end of an old highlight and dragging further).
- **Initial fix (incomplete)**: anchored expansion on the mark's first/last text-node descendants. This turned out to be necessary but insufficient.
- **Second pass** (found while writing tests): the DOM Range mutation rules collapse **any** range boundary whose container is an inclusive descendant of a removed node — even text-node-level boundaries. When `mark.replaceWith(...childNodes)` runs, the text node survives (it gets reparented), but the range holding a boundary on it gets collapsed to `(parent-of-mark, index-of-mark)` — an element-level boundary BEFORE the reparented text node. The range then covers only the text before the mark, not the text that used to be inside it. The symptom in the "merge from right" test was a merged highlight reading "jewels. A " instead of "jewels. A mad boxer shot a quick,".
- **Final fix**: capture the expanded start/end as raw `(node, offset)` tuples BEFORE the unwrap (NOT as `range.setStart/setEnd` calls, since those go through the same DOM Range mutation rules). Unwrap the marks. Then reconstruct the range via `range.setStart(capturedStart, ...)` / `range.setEnd(capturedEnd, ...)` on the now-reparented text nodes. Used temporary ranges + `.collapsed` check for the boundary comparisons (a collapsed temp range means the two boundaries coincide — i.e. the mark's start/end is equal to the current merged start/end, no expansion needed).

### Midnight theme lost its parchment light variant during rebase

- User report: "light mode doesn't work in midnight, what happened to its light version" — pressing `d` in reader mode (the light/dark toggle at `src/utils/reader.ts:2094-2099`) on the midnight theme had no visible effect. Class flipped correctly; no CSS picked it up.
- Root cause: the parchment light + near-black dark variant of midnight was originally shipped in commit `7dd38dc "Midnight theme (parchment light / dark), citation toggle, shortcuts"` (Apr 7), with the light values at the top of the rule and dark values nested under `&.theme-dark`. During the rebase tracked by branch `codex/pre-rebase-custom-20260410`, that rule was replaced by commit `5c39263 "Add Midnight reader theme"` — a dark-only reversion with a hard `color-scheme: dark` at the end and no `.theme-dark` block. Net: midnight could never render light because there were no light variables defined, and `color-scheme: dark` also forced form controls / scrollbars to stay dark regardless of class.
- The `d` shortcut itself works on every other theme (ayu, catppuccin, etc.) because those themes define both variants. Only midnight was missing.
- **Fix**: restored the full two-variant block in `src/styles/_reader-themes.scss` at `[data-reader-theme="midnight"]`. Light (parchment `#f4f0e8` bg, warm stone `#3a3226` text, muted earthy accents) at the top, dark (`#0d0d0d` bg, `#d4d4d4` text, the original near-black set) inside `&.theme-dark, .theme-dark`. Dropped the standalone `color-scheme: dark;` since it conflicts with the toggle; other themes don't set `color-scheme` either.

## 2026-04-12

### Auto-clip "[AutoClip] extract failed" on ngrok.com (and others)

- User report: `[AutoClip] extract failed {url: 'https://ngrok.com/blog/quantization'}` printed on every highlight. They pushed back on my initial explanation (a Defuddle parse failure) with: "reader mode works though? how can that happen if defuddle is failing. manual save also works, automatic save shouldve done the same as the manual anyway? why the drift." — which was exactly right.
- Root cause: **four Defuddle call sites, three different behaviors**. I mapped them all:
  1. `src/utils/reader.ts:789` — reader mode uses `parseAsync()` (no try/catch, no fallback).
  2. `src/content.ts:303` — popup "Save to Obsidian" (`getPageContent`) uses `parseAsync()` with an 8s timeout, `.catch(() => defuddle.parse())` on any failure.
  3. `src/content.ts:224` — auto-clip (`extractPageMarkdown`) used **sync `.parse()`** with no fallback.
  4. `src/content.ts:238` and `src/content.ts:263` — `copyMarkdownToClipboard` and `saveMarkdownToFile` used sync `.parse()` with no fallback.
- Defuddle's sync `.parse()` can throw on pages where `parseAsync()` succeeds: `parseAsync` awaits async variable extractors (`{{transcript}}`, schema.org resolvers, deferred content) that the sync path can't handle. On the ngrok blog, sync throws, async doesn't. So reader mode (parseAsync) and popup save (parseAsync with fallback) both worked, but auto-clip (sync only) failed, and the mismatch looked like "Defuddle broken" when it was actually "we pick the wrong method here".
- **Fix**: unified `extractPageMarkdown` in `src/content.ts:221` to use the same parseAsync + 8s timeout + sync fallback pattern as `getPageContent`. Also added the same 3s `flattenShadowDom` race that `getPageContent` uses, so flatten can't hang extract either. `extractPageMarkdown` is called only by `autoClipPage` in `src/utils/reader-highlights.ts:405`, so the fix is contained — no other callers to worry about.
- Didn't touch paths 4 (copy/save). Those are user-initiated and the user is in a position to notice + retry if they fail; auto-clip is a fire-and-forget side effect that spams logs on every highlight, so it's the one that needs the robustness.
- Didn't touch path 1 (reader mode). Reader mode *already* uses parseAsync and works per the user's own report; adding a fallback there is a nice-to-have but not this bug.

### Auto-clip should just do what the S button does

- User pushed back on the parseAsync fix: "it should do whatever the s button does". Right call. Running Defuddle at all (sync or async) inside reader mode is redundant — reader mode already extracted and cleaned the article into a top-level `<article>` element. `quickSaveToObsidian` (`reader.ts:841-903`, the S-key shortcut) skips Defuddle entirely and just runs `article.innerHTML` through `createMarkdownContent` from `defuddle/full`. That's why S works where auto-clip didn't: no parse call to fail.
- **Fix**: rewrote `autoClipPage` in `src/utils/reader-highlights.ts` to mirror `quickSaveToObsidian` exactly when reader mode is active.
  - Detects reader mode via `document.documentElement.classList.contains('obsidian-reader-active')`.
  - If active AND an `<article>` element exists: grabs `h1` text as title, strips any text-fragment directive from the URL (`#:~:text=...`), dynamically imports `createMarkdownContent` from `defuddle/full`, converts `article.innerHTML` to markdown directly. No Defuddle parse call.
  - If NOT in reader mode: falls back to `extractPageMarkdown` message (which now uses parseAsync + sync fallback from yesterday's fix). Preserves existing raw-page auto-clip behavior.
  - Aligns every detail with quickSave that was drifting: title sanitization (`[\\/:*?"<>|]` + 200-char cap, not the old looser regex), frontmatter layout (multiline with `tags:\n  - clippings` block), date format (`YYYY-MM-DD` not full ISO).
  - On successful clip, sets `document.documentElement.setAttribute('data-obsidian-note-path', filePath)` from the plugin response — same as quickSave does. Prevents auto-clip from firing again on the same page and makes the S key's "Already saved to Obsidian" guard trigger correctly if the user hits S after auto-clip.
  - Added an early `dataset.obsidianNotePath` guard at the top of `autoClipPage` so the function short-circuits on already-linked pages before any work.
- Net result: highlighting in reader mode on ngrok.com/blog/quantization (or any page where sync Defuddle throws) now creates a clean Obsidian note via the same path the S key uses, with no parse failures in the console.

### Drag-select yellow disappeared in reader mode

- User report: "what did you do to selector styles. its not a highlight anymore when selecting, just the default". Drag-selecting text in reader mode showed the reader theme's (muted blue/grey) selection color instead of the highlight yellow.
- Root cause: a regression I introduced on 2026-04-11 when I dropped `!important` from the `*::selection` rule in `src/highlighter.scss`. My note at the time claimed "`body.obsidian-highlighter-active *::selection` has specificity (0,1,2) — enough to beat plain `::selection` (0,0,1) on any site, and source-order wins for content-script CSS." That was only true for the raw-page case. Inside reader mode, `src/reader.scss:169-171` has `.obsidian-reader-active body ::selection { background-color: var(--text-selection); }`, which is NOT a "plain" `::selection` — it nests under `.obsidian-reader-active body`, giving it specificity (0,1,2), the exact same as the highlighter rule.
- Both rules match inside reader mode when the highlighter is active. With equal specificity, source order decides. `reader.scss` is injected via `chrome.scripting.insertCSS` *after* `highlighter.scss` loads via `content_scripts`, so reader.scss wins — and the theme's `var(--text-selection)` (a muted blue) paints the drag selection instead of the yellow. On raw pages outside reader mode, reader.scss isn't loaded, so the highlighter rule wins — which is why the bug only showed up inside reader mode.
- **Fix**: restored `background-color: ... !important; color: ... !important;` on `body.obsidian-highlighter-active *::selection` in `src/highlighter.scss:158-164`. Added a load-bearing comment explaining exactly why the `!important` is not cargo and must not be removed again.
- Didn't touch reader.scss. `.obsidian-reader-active body ::selection` still governs selection color in reader mode when the highlighter is off, which is the correct default — users who just enter reader mode without intending to highlight get the theme's selection color. Only when highlighter is on should the yellow override kick in, and `!important` on the highlighter rule is the narrowest fix that achieves that.

### Wikipedia phonetic pronunciations disappeared in reader mode

- User report: "wikipedia linked phonetics don't appear on reader mode. like /əˈpɒkrɪfə/ from https://en.wikipedia.org/wiki/Apocrypha".
- Root cause: Defuddle's partial-selector clutter removal pass has a false positive on Wikipedia's pronunciation markup. Bisected the Defuddle pipeline by flipping each removal pass off in isolation:
  | Option flipped off | IPA preserved? |
  |---|---|
  | default (everything on) | NO |
  | `removeHiddenElements: false` | NO |
  | `removePartialSelectors: false` | **YES** |
  | `removeLowScoring: false` | NO |
  | `standardize: false` | NO |
  Turning on debug mode and filtering the removals list for entries whose `text` contained the phonetic string produced a single hit:
  ```
  step: removeBySelector | selector: -comment | reason: partial match: -comment
  text: "/əˈpɒkrɪfə/"
  ```
  The pattern `'-comment'` at `node_modules/defuddle/dist/constants.js:394` is meant to strip comment sections (`post-comments`, `user-comment-box`, etc.). Wikipedia wraps phonetic pronunciation tooltips in `<span class="rt-commentedText nowrap">` where `rt` stands for "ruby text" (phonetic annotation) and `commentedText` means "text that has a tooltip annotation", not "user comment". The substring `-comment` inside `rt-commentedText` is a false positive — Defuddle sees the class and strips the whole span, taking the IPA inside with it.
- Verified the diagnosis end-to-end: pulled the real Wikipedia page via curl, ran it through Defuddle locally via `linkedom + node_modules/defuddle/dist/index.full.js`, confirmed the IPA is stripped. Then verified the fix: stripping only the `rt-commentedText` class from offending nodes before running Defuddle preserves the full phonetic transcription including the inner `<a href="/wiki/Help:IPA/English">` link structure.
- **Fix**: added a two-line DOM prep step in `Reader.extractContent()` at `src/utils/reader.ts:789`, immediately before the `new Defuddle(doc, ...)` call:
  ```ts
  doc.querySelectorAll('.rt-commentedText').forEach(el => {
      el.classList.remove('rt-commentedText');
  });
  ```
  Just the one class is removed; the rest of the markup (span nesting, `IPA`, `nopopups`, `noexcerpt` classes, `lang="en-fonipa"` attribute, the nested per-character `<span title="...">` structure) is untouched. Defuddle then no longer matches the wrapper via partial selectors, leaves the IPA in the extracted content, and reader mode renders it normally.
- Didn't fork Defuddle or monkey-patch its PARTIAL_SELECTORS list. The fix is narrow, obvious, and located exactly where it matters — if another site's pronunciation or annotation wrapper gets caught by a different false-positive pattern, we can extend this block with another `querySelectorAll().classList.remove()` line.
- Auto-clip inherits the fix for free: it now reads from the already-extracted `<article>` element (the S-key path from earlier today), which is produced by the same reader-mode Defuddle run that now preserves the IPA.

### Regression tests for all changes today

- Added 4 new tests covering every fix shipped today. Full suite: 36 tests, 20.6 seconds, all passing.
  1. **`::selection rule: !important assertions`** — updated existing `highlight-rendering.spec.ts` test to verify `background-color` and `color` both have `!important` in the compiled `dev/highlighter.css`. Guards against the reader-mode same-specificity cascade regression.
  2. **`midnight theme: both parchment-light and near-black-dark CSS variables defined`** — static test in `highlight-rendering.spec.ts` that parses `src/styles/_reader-themes.scss`, verifies the midnight block contains both `#f4f0e8` (parchment light) and `#0d0d0d` (near-black dark) variables, and does NOT have a standalone `color-scheme: dark` (the revert's bug). Guards against the rebase regression.
  3. **`midnight theme: d-key toggles between parchment-light and near-black-dark`** — runtime test in `sync.spec.ts`. Enters reader mode, sets midnight theme + `theme-light` class, asserts computed bg is `rgb(244, 240, 232)`, presses `d`, asserts bg changes to `rgb(13, 13, 13)`, presses `d` again, asserts it toggles back. End-to-end proof that the CSS variables AND the keydown handler both work.
  4. **`Wikipedia IPA phonetics survive reader-mode extraction`** — runtime test in `sync.spec.ts`. Loads a new `e2e/fixtures/wikipedia-ipa.html` fixture with real Wikipedia IPA markup (`<span class="rt-commentedText"><span class="IPA">...</span></span>`). This URL is NOT linked to any vault note, so reader mode falls through to Defuddle. Asserts the IPA characters (`ə`, `ɒ`, `krɪf`) are present in the extracted article, and that the parentheses after "Apocrypha" are not empty.
- New fixture: `e2e/fixtures/wikipedia-ipa.html` — minimal page with the exact Wikipedia `<span class="rt-commentedText nowrap">` → `<span class="IPA nopopups noexcerpt">` → per-character `<span title="...">` structure for `/əˈpɒkrɪfə/`. Not linked to any vault note so Defuddle extraction runs.
- Test gotcha: Defuddle's standardization pass inserts spaces between the single-character `<span>` elements, so `textContent` has `ə ˈ p ɒ k r ɪ f ə` (spaced). The test strips whitespace before checking character substrings, so it's tolerant of Defuddle's formatting without being too loose.

### Auto-clip toast unified with S-key toast
- Auto-clip was using `showPluginOfflineToast` (grey `#1a1a1a` bg, different ID/timing) while the S-key used `Reader.showToast` (green `#2a4a2a` bg). Unified by extracting `showReaderToast(message, isError?)` in `reader-highlights.ts` — same look, same ID (`obsidian-reader-toast`), same 2s duration. Both auto-clip and S-key now use it. `Reader.showToast` delegates to the shared function.

### YouTube embed: strip playlist params to prevent auto-advance
- User report: "in youtube view sometimes the video changes to next video by itself, not even changing the transcripts" — happens at the START of the video, not the end. Root cause: the YouTube iframe embed URL includes `list=` (playlist ID) and `index=` params. YouTube's embed player sees the playlist context and can auto-advance on load. The transcript is baked for a single video.
- Fix: strip `list` and `index` params from the iframe URL in `src/utils/reader-transcript.ts:119-122` when setting up the JS API. Forces the embed to play just the single video.

### Clippings organized into per-author (or per-domain) subfolders
- User request: "when we are saving things, things go to their related folder, like same author goes to its own folder"
- Changes:
  - **`reader.ts`**: after Defuddle extraction resolves, store `data-reader-author` and `data-reader-domain` on `documentElement` so the save paths can read them.
  - **`quickSaveToObsidian`** (S key): reads `dataset.readerAuthor` / `dataset.readerDomain`. Computes `savePath = Clippings/${author || domain}` (falls back to `Clippings/` if neither available). Also adds `author` field to frontmatter when present.
  - **`autoClipPage`** (first-highlight auto-save): same logic — reads the data attributes, uses `author || domain` for subfolder, adds `author` to frontmatter.
  - Both paths sanitize the subfolder name with the same `[\\/:*?"<>|]` character set as the title.
  - Attributes cleaned up in `reader.ts:restore()` on reader mode exit.
- Examples: an article by "John Gruber" on daringfireball.net → `Clippings/John Gruber/article.md`. A page with no author on reddit.com → `Clippings/reddit.com/article.md`. A page with neither → `Clippings/article.md`.

## 2026-04-12 (session 2)

### Theme persistence feature
- **Problem**: The d-key shortcut in reader mode toggled `theme-light`/`theme-dark` CSS classes but never persisted the choice. Exiting and re-entering reader mode (or navigating to a new page) reset to the default `auto` appearance.
- **Root cause**: The d-key handler directly manipulated CSS classes without calling `updateThemeMode()`, which handles both the visual toggle AND settings persistence.
- **Fix**: Changed d-key handler to call `this.updateThemeMode(doc, newMode)` and sync the settings bar dropdown via `data-setting-id="reader-appearance"`.
- **Storage bug discovered**: `browser.storage.sync.set()` called from content scripts injected via `chrome.scripting.executeScript` silently fails to persist. Discovered after extensive debugging — the initial `saveSettings` from `apply()` worked, but subsequent calls from event handlers did not.
- **Fix for storage**: Route all `saveSettings()` calls through `browser.runtime.sendMessage({ action: 'saveReaderSettings', settings })` to the background script, which has reliable `storage.sync` access. Added `saveReaderSettings` handler in `background.ts`.
- **Build system lesson**: `bun run build` outputs to `dist/`, but e2e tests load the extension from `dev/`. Must use `bun run build:chrome:dev` (or `bun run test:e2e`) to build to the correct directory. Wasted significant debugging time running tests against stale code.
- **Test changes**: Updated midnight theme test to set theme through `storage.sync` pre-seeding (via service worker) instead of direct DOM manipulation, since `updateThemeMode` now also calls `applyTheme()` which reads the effective theme from settings.
- **New test**: "theme persistence: d-key toggle survives navigation to a new page" — presses d, opens a fresh tab, verifies dark theme persists.
- **Result**: 44 tests pass (43 → 44), all against real plugin, no mocks.

## 2026-04-14

### Goal
- Make `bussproofs` proof trees render correctly in Obsidian notes created by the clipper, while preserving actual `bussproofs` syntax instead of converting to a fallback math representation.
- Record the full debugging path, including dead ends, in one place.

### What the user reported
- Initial screenshot: raw `\begin{prooftree} ... \end{prooftree}` showing in a saved note, not in reader mode.
- Important correction from user: the failure was in Obsidian note rendering, not the extension reader.

### First diagnosis
- The clipper was saving proof trees in forms Obsidian/MathJax did not like:
  - wrapped in `$...$` or `$$...$$` in ways that left nested math delimiters inside `\AxiomC{...}`
  - malformed mixed wrappers such as `$\begin{prooftree} ... \end{prooftree}\)`
- Even when the note looked closer to valid `bussproofs`, Obsidian still did not render it because the runtime `bussproofs` package load was unreliable.

### Clipper-side fixes

#### Saved markdown normalization
- Added `src/utils/prooftree-markdown.ts`
  - normalizes malformed saved proof-tree markdown
  - strips nested inner delimiters inside proof-tree command arguments
  - preserves actual `bussproofs` syntax
  - injects `\require{bussproofs}` into proof-tree expressions
- Wired it into all clip/save paths:
  - `src/utils/reader.ts`
  - `src/utils/reader-highlights.ts`
  - `src/content.ts`
  - `src/api.ts`
  - `src/utils/content-extractor.ts`

#### Regression coverage
- Added tests:
  - `src/utils/prooftree-markdown.test.ts`
  - `src/utils/prooftree-clip-output.test.ts`
  - reused `src/utils/reader.test.ts`
- The intent of these tests:
  - pin the broken saved-note shapes we actually observed
  - ensure future clipping keeps real `bussproofs`
  - ensure malformed nested delimiters are cleaned before save

### What worked on the clipper side
- Existing broken notes were successfully rewritten into cleaner proof-tree forms.
- The main SEP clipping note was regenerated from the local raw fixture and restored to valid proof-tree math blocks.
- The test note was reduced to a minimal single proof-tree block for faster debugging.

### What did NOT solve the problem

#### 1. Old `obsidian-latex` / Extended MathJax plugin
- The plugin was installed but not enabled.
- Enabling it plus adding `preamble.sty` did not solve rendering.
- Reading its source showed it only loaded the preamble text; it did not explicitly and robustly load `bussproofs` for the active MathJax instance.
- A local patch was attempted to force-load `require` and `bussproofs`.
- Result:
  - first patch caused plugin load failures
  - defensive patch stopped the load failure
  - but actual proof-tree rendering still failed in notes

#### 2. Converting proof trees to `\cfrac` / `\genfrac`
- I briefly switched to a “just make it standard MathJax” strategy by converting `prooftree` to `\cfrac`.
- User explicitly rejected this because the requirement is to keep actual `bussproofs`.
- That path was reverted.

### Important discovery from console logs
- The user supplied logs from `reading-selection-highlight`:
  - `[bp] installBussproofs called`
  - `[bp] MathJax ready`
  - `[bp] ConfigurationHandler found`
  - `[bp] bussproofs already in MathJax._`
  - `[bp] bpConfig found`
  - `[bp] already installed, re-typesetting...`
  - `[bp] re-typeset done`
- This proved that `reading-selection-highlight` was already installing `bussproofs` into Obsidian's MathJax.
- So the remaining issue was not package registration alone.

### Custom local Obsidian plugin attempts

#### Attempt A: custom `bussproofs-renderer` plugin
- Created a new vault-local plugin at:
  - `Grimoire/.obsidian/plugins/bussproofs-renderer`
- Disabled `obsidian-latex` in `community-plugins.json`
- Goal:
  - bypass Obsidian's inconsistent preview behavior
  - detect proof-tree note content directly
  - ask MathJax to typeset just those proof-tree blocks
  - log every failure clearly

#### Attempt B: first implementation bug
- The generated plugin file was mangled by shell escaping and failed syntax check.
- Fixed by rewriting the plugin file literally and validating with `node --check`.

#### Attempt C: wrong target layer in DOM
- Plugin initially found proof trees and said it “rendered” them, but the visual result was duplicated/garbled.
- Root cause: it was targeting duplicate/wrong wrapper layers.
- Fix:
  - narrowed targeting to real `.math-block` nodes
  - render in place
  - mark processed blocks

#### Attempt D: plugin loaded but found nothing
- Added startup marker versions:
  - `loading v0.0.2`
  - `loading v0.0.3`
  - `loading v0.0.4`
  - `loading v0.0.5`
- This confirmed Obsidian was actually loading the latest file and not a cached copy.
- Added lifecycle logging:
  - `postprocessor`
  - `file-open`
  - `active-leaf-change`
  - `layout-ready`
  - explicit rescans
- Added candidate-root logging per markdown leaf:
  - `view.containerEl`
  - `view.contentEl`
  - `previewMode.containerEl`
  - `.markdown-preview-view`
  - `.markdown-reading-view`
  - `.markdown-rendered`
- This found the correct root: `view.containerEl` for the test note.

#### Attempt E: decisive MathJax error surfaced
- Once the correct root was found, the plugin logged the real error:
  - `\supset is only supported in math mode`
- The failing LaTeX was:
  - `\begin{prooftree} \AxiomC{A \supset B} \AxiomC{A} \BinaryInfC{B} \end{prooftree}`
- Root cause:
  - `bussproofs` arguments like `\AxiomC{...}` are parsed as text unless the content inside is explicitly math.
  - So `\AxiomC{A \supset B}` is wrong for MathJax `bussproofs`.

#### Attempt F: proof-tree argument normalization
- Patched the custom plugin to rewrite proof-tree command arguments before calling MathJax:
  - `\AxiomC{A \supset B}` → `\AxiomC{$A \supset B$}`
  - same idea for `UnaryInfC`, `BinaryInfC`, `TrinaryInfC`, `RightLabel`, `LeftLabel`
- Startup marker bumped to `loading v0.0.5`
- Result:
  - success
  - the plugin found one proof-tree target
  - rendered it successfully in the test note

### Current working state
- The custom plugin `bussproofs-renderer` is active.
- `obsidian-latex` is disabled.
- `reading-selection-highlight` still logs that it installs `bussproofs`.
- The test note renders a proof tree in Obsidian.
- The visual result is now “rendered but rough”, which is a styling/layout refinement problem rather than a parser/load failure.

### What worked
- Reproducing the actual error instead of assuming package-loading was enough.
- Instrumenting the custom plugin heavily:
  - explicit version markers
  - file-open / postprocessor / rescan logs
  - candidate root discovery
  - exact MathJax error capture
- Targeted normalization of `\AxiomC{...}` and related commands to wrap arguments in math mode.

### What did not work
- Relying on `obsidian-latex` alone
- Assuming `\require{bussproofs}` in the note would be sufficient
- Assuming `reading-selection-highlight` package registration alone implied note rendering would work
- DOM targeting based on the wrong preview wrapper
- Early custom plugin versions that replaced the wrong DOM layer
- The temporary `\cfrac` conversion path (reverted)

### Files touched during this session

#### Clipper repo
- `src/utils/prooftree-markdown.ts`
- `src/utils/prooftree-markdown.test.ts`
- `src/utils/prooftree-clip-output.test.ts`
- `src/utils/reader.ts`
- `src/utils/reader-highlights.ts`
- `src/content.ts`
- `src/api.ts`
- `src/utils/content-extractor.ts`

#### Vault / Obsidian
- `Grimoire/.obsidian/community-plugins.json`
- `Grimoire/.obsidian/plugins/obsidian-latex/main.js` (temporary patching attempt)
- `Grimoire/.obsidian/plugins/bussproofs-renderer/main.js`
- `Grimoire/.obsidian/plugins/bussproofs-renderer/manifest.json`
- `Grimoire/preamble.sty`
- `Grimoire/Bussproofs Test.md`
- `Grimoire/Clippings/stanford.edu/Propositional Logic (Stanford Encyclopedia of Philosophy).md`

### Notes on unresolved follow-up
- The proof tree now renders, but the layout/spacing is not yet polished.
- The next step is visual refinement:
  - spacing
  - centering
  - handling multiple proof trees in one display block
  - deciding whether to keep using MathJax output directly or decorate it

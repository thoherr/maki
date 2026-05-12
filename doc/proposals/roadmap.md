# MAKI Roadmap

Living document tracking planned enhancements. Previous proposals (all implemented or deferred) are in `archive/`. Active proposals are in `doc/proposals/`.

Current version: **v4.5.6** (2026-05-11)

---

## Active Proposals

### Manual Translation (i18n)

Produce the MAKI user manual in English and German from a single source using inline language markers. See `doc/proposals/manual-i18n.md`.

**Status:** Proposal written, not started.

**Complexity:** Low (tooling), Medium (translation effort).

---


## Tier 1 — High Value

### Auto-Stack by Similarity (Catalog-wide) *(Pro)*

Discover natural visual clusters across the catalog and propose stacks. Phase 3 of the similarity browse proposal (Phases 1–2 implemented in v4.0.2). See `archive/proposal-similarity-browse-and-grouping.md`.

**Scope:**
- `maki auto-stack --threshold 85` — scan all embedded assets, cluster by similarity, propose stacks
- Pick selection: highest-rated in each cluster
- `--dry-run` for review, `--apply` to create
- Clustering algorithm: greedy connected-components over embedding similarity matrix

**Complexity:** Medium. Embedding infrastructure and stacking exist; needs clustering algorithm and CLI command.

### Watch Mode

Auto-import and sync on filesystem changes. After a CaptureOne session, new files appear in the catalog without manual `maki import`.

**Scope:**
- `maki watch [PATHS...] [--volume <label>]` — monitors directories for new/changed files
- Poll-based initially (simple, cross-platform); fsevents/inotify optional later
- Triggers import for new files, refresh for changed recipes
- Configurable via `[watch]` section in `maki.toml` (poll interval, exclude patterns)
- Runs as foreground process (like `maki serve`), logs activity to stderr

**Complexity:** Medium. Core import/refresh logic exists; needs a polling loop and file-change detection.

### GPU-Accelerated Embeddings (Linux/Windows) *(Pro)*

SigLIP embedding generation on CPU is slow for large catalogs. GPU backends make batch embedding practical at scale.

**Status:** CoreML (macOS) included automatically in Pro builds since v4.1.0. Linux/Windows pending.

**Open:**
- CUDA execution provider for Linux (requires `ort/cuda` feature, CUDA Toolkit + cuDNN)
- DirectML execution provider for Windows (requires `ort/directml` feature)
- Testing and packaging across platforms

**Complexity:** Low for adding providers (code pattern exists), high for testing/packaging.

### IPTC/EXIF Write-Back *(Pro)*

Write metadata changes back into JPEG/TIFF files directly, not just XMP sidecars. Some workflows and stock photo submissions require embedded metadata.

**Scope:**
- `maki writeback --embed` writes rating, tags, description, label into file's embedded metadata
- IPTC keywords, caption/description, urgency (mapped from rating)
- Preserves existing embedded metadata; only updates DAM-managed fields
- Re-hashes file after write, updates variant content hash

**Complexity:** High. Modifying binary file metadata without corruption requires careful handling.

---

## Tier 2 — Workflow Convenience

### Mobile & Tablet Browsing

The web UI works on mobile but isn't optimized. Combined with read-only multi-user access, this enables "show photos to clients on iPad" and remote browsing from any device on the LAN.

**Scope:**
- Responsive layout improvements: touch-friendly grid, swipe navigation in lightbox
- Collapsible filter bar for small screens
- `--read-only` mode (disables all write endpoints) for safe sharing
- Optional basic auth (`[serve] username/password` in `maki.toml`)

**Complexity:** Medium. CSS/layout work plus read-only mode (which is mostly route-level guards).

### Advanced Contact Sheet Templates *(Pro)*

Professional-grade contact sheet layouts beyond the current defaults. Templates for client proofing, portfolio review, and print production.

**Scope:**
- Additional layout presets (grid with metadata overlay, filmstrip, portfolio pages)
- Custom template system (user-defined layouts via config)
- Gated behind `pro` feature flag

**Complexity:** Medium.

### Web UI Export Progress

The ZIP export modal shows "Preparing..." with no progress feedback.

**Scope:**
- Server sends export plan summary (file count, estimated size) before starting
- Client shows a progress bar or asset counter
- Warn before very large downloads (> 1 GB)

**Complexity:** Low-Medium.

### Volume Health Monitoring

Surface drive health and verification staleness proactively.

**Scope:**
- Per-volume staleness warnings in `maki stats --verified`
- `maki verify --report` health summary
- Web UI volume health indicators on backup page

**Complexity:** Low.

---

## Tier 3 — Polish & Future

### Undo / Edit History

Track metadata changes with timestamps for audit trail and undo capability.

**Scope:**
- `asset_history` table: asset_id, field, old_value, new_value, timestamp, source
- `maki history <asset-id>` and `maki undo <asset-id>`
- Web UI history panel on detail page

**Complexity:** High.

### Tethered Shooting

Live import during a connected camera session. Essentially watch mode + auto-import + immediate preview in the web UI.

**Scope:**
- Build on watch mode (Tier 1) with lower latency
- Auto-open imported assets in the web UI
- CaptureOne hot folder integration as primary use case

**Complexity:** Medium (requires watch mode first).

### Print Workflow

Print selected assets with proper page layout. Currently only contact sheets are supported.

**Scope:**
- `maki print` command or web UI print button
- Single-image and multi-image layouts with configurable margins
- ICC color profile support for accurate print colors

**Complexity:** High. Color management is complex; layout engine already exists in contact sheet code.

---

## Completed (Archived)

Design documents for completed features are in `doc/proposals/archive/`. Key milestones:

- **v0.1–v1.0**: Core CLI — import, search, metadata, volumes, previews
- **v1.1–v1.4**: Storage workflow — dedup, backup-status, copies filter, volume purpose
- **v1.5–v1.8**: Web UI — lightbox, dark mode, calendar, map, compare, facets, stacks, collections
- **v1.8.9**: Export command
- **v2.0–v2.1**: AI — auto-tag, embeddings, similarity search, suggest tags
- **v2.2**: Performance — SQLite pragmas, single connection, denormalized columns
- **v2.3**: Stroll, sync-metadata, comprehensive cleanup, faces/people
- **v2.4**: Contact sheet export, split command, alternate variant role, CoreML GPU, VLM descriptions
- **v2.5**: Text-to-image search, auto-describe during import, concurrent VLM, analytics, batch relocate, drag-and-drop, per-stack expand/collapse
- **v3.0**: Interactive shell — REPL with variables, tab completion, script files
- **v3.1**: Preview command, consistent positional query and shell variable expansion
- **v3.2**: Web UI export ZIP, batch delete, shell export, per-model VLM config, verbose threading, documentation consolidation
- **v4.0**: MAKI rebrand (binary `dam` → `maki`, config `dam.toml` → `maki.toml`, full visual rebrand), branded PDF manual
- **v4.0.1–v4.0.12**: Default browse filter, similarity browse, Windows support, CI/CD, unified numeric filters, XMP writeback safeguard, cheat sheet, automated releases, branded screenshots
- **v4.1.x (Video Playback)**: HTML5 video player on detail page and lightbox, duration badges on browse cards, video metadata extraction via ffprobe (duration, codec, resolution, framerate) at import time, `generate-previews --force` backfills video metadata for existing assets. Phase 2 `duration:` and `codec:` search filters implemented (duration uses denormalized `video_duration` column with full `NumericFilter` support; codec uses denormalized `video_codec` column with LIKE matching). Remaining Phase 2 filter: `resolution:` (but `width:`/`height:` already cover this).
- **v4.1.x**: MAKI Pro edition (`pro` feature flag, `-pro` release artifacts), VLM/writeback/sync-metadata gated behind Pro, search filter reference card, `volume split`/`rename`, `edit --clear-tags`, improved `scattered:` filter with `/N` depth, star rating filter UX, consistent *(Pro)* markers in manual, repo cleanup (`doc/images/`, `doc/quickref/`)
- **v4.2.x**: Card-first workflow (media volume purpose, create-sidecars, auto-label, volume list filters), import profiles, video proxy generation with hover-to-play, user guide improvements (17 items across 3 passes)
- **v4.3.x**: Tag hierarchy separator aligned with LR/C1 (`|` and `>`), tag rename/clear/expand-ancestors/export-vocabulary subcommands, ancestor expansion matching CaptureOne convention, vocabulary.yaml for planned tag hierarchy with autocomplete integration, git-based catalog backup, BTreeMap for deterministic YAML, Tagging Guide chapter, configurable `[group] session_root_pattern` regex
- **v4.3.12**: Volumes page in web UI with register/rename/purpose/remove and import dialog with live SSE progress, `*` wildcards in `path:` filter (full pattern matching with leading-`*` opt-in for slow scans), SigLIP 2 multilingual model variants (`siglip2-base-256-multi`, `siglip2-large-256-multi`) for `text:` search in German, French, Spanish, Italian, Japanese, Chinese, etc. — see `archive/proposal-multilingual-text-search.md`
- **v4.3.13**: License compliance infrastructure — `cargo-about` generates `THIRD_PARTY_LICENSES.md` shipped in every release archive, `cargo-deny` validates allowed-license allowlist on every CI run, new `maki licenses` CLI command, new manual appendix `reference/11-licenses.md` covering MAKI license / Rust crates / AI models / external tools. Dropped `viuer` dependency (last LGPL-3.0 transitive dep) → fully permissive dependency tree. Simplified `maki preview` to always open in OS default viewer (removed inline terminal display and `--open` flag). Doc fix: clarified `maki embed` does NOT need `--force` when switching AI models — embeddings are keyed per `(asset_id, model_id)`, so a model switch only generates the missing embeddings. New "Switching models" section in setup guide.
- **v4.3.14–v4.3.19**: Tag rename in web UI (pencil icon + autocomplete modal), `scattered:`/`copies:` semantics fixes (distinct session roots / distinct volumes), new default subject vocabulary branches (style / condition / mood), code-quality pass (route handler deduplication, `unwrap()` → `expect()`, lowercase error messages, section markers in the 3 largest source files).
- **v4.3.20**: `label:none` search filter and browse UI icon (matching `rating:0` / `volume:none` patterns), stronger active-state styling on ∅ filter icons, `tag rename =` now uses leaf-only semantics (consistent with search `=`), hierarchical tag search matches at any level (`tag:Altstätten` finds `location|Switzerland|Altstätten`), quoting hint on empty search results, asset-ID whitespace trimming (handles copy-paste NBSP), browse page person filter preserved across pagination/sort, unnamed face clusters browseable from people page and asset detail, `stack from-tag --remove-tags` cleans up orphan tags too (not just newly-stacked), quickref cheat sheet trimmed to 2 pages.
- **v4.4.0**: Face recognition pipeline rewrite — ArcFace ResNet-100 **FP32** model (replacing INT8) with proper **5-point landmark alignment** to the canonical 112×112 template, **corrected preprocessing** (raw pixel values; the model's internal Sub/Mul nodes do the normalization — external normalization was double-normalizing and collapsing embeddings), **agglomerative hierarchical clustering** (average linkage / UPGMA, order-independent) replacing greedy single-linkage, **model version tracking** via new `recognition_model` column on faces (schema v5→v6, faces from an older model variant are skipped by clustering with a warning), new defaults (`face_cluster_threshold` 0.5→0.35, `face_min_confidence` 0.5→0.7), three new diagnostic/maintenance commands: `maki faces clean` (delete unassigned orphans), `maki faces similarity` (histogram + percentile stats for picking a threshold), `maki faces dump-aligned` (save the 112×112 aligned crops for visual verification), `--min-confidence` flag on `cluster`, `--force` on `detect`. Full upgrade path documented in the user guide and CHANGELOG.
- **v4.4.1**: People workflow UX — batch merge UI on the `/people` page (checkbox-select any N clusters, pick the merge target with a bullseye badge, confirmation modal with thumbnails), automatic **merge suggestions** panel that surfaces pairs of clusters whose centroid embeddings are similar enough to likely be the same person (common after auto-clustering), client-side name filter on the people grid, searchable typeahead combobox replacing the plain `<select>` in the face-assign dropdown on the asset detail page. New endpoint `GET /api/people/merge-suggestions`; `POST /api/people/{id}/merge` also accepts a plural `source_ids` array for batch merges.
- **v4.4.2**: Filter bar refinements — the browse filter bar's person picker is now a chip-based multi-select on the same row as tag chips (layout: `[tags] [people] [path]`). **Multiple tag chips and multiple person chips now AND** (asset must contain all selected), fixing a bug where chip selection was silently OR'd at the catalog level. Comma-OR (`tag:a,b`, `person:a,b`) still works in the q field for power users. Person chips are tinted teal to distinguish from salmon tag chips; same interaction grammar (type, ↑/↓/Enter, backspace to remove last chip).
- **v4.4.3**: `face_scan_status` column on assets (schema v6→v7) so `faces detect` no longer re-scans zero-face assets on every run. Persisted to both SQLite and YAML sidecar (maintaining the dual-storage invariant). Dual-storage audit fixed `faces.recognition_model` round-trip through faces.yaml and added `post_migration_sync` hook. New "Visual Discovery" user-guide chapter (12) covering face recognition, similarity search, and stroll as workflows.
- **v4.4.4**: Tag search marker swap — `tag:=` is now **whole-path match** (exact tag value equality, reads naturally as "equals"), `tag:/` is leaf-only-at-any-level. Breaking change vs v4.4.3 where the assignments were reversed. Tri-state tag chip toggle cycles ▼ → = → /. Disambiguates same-named tags at different hierarchy levels (the "Legoland" problem — root-level `Legoland` vs `location|Denmark|Legoland` vs `location|Germany|Legoland`).
- **v4.4.5**: Maintenance release. Internal refactoring of the four largest files (`main.rs`, `web/routes.rs`, `catalog.rs`, `asset_service.rs`) — `run_faces_command` lifted out of `run_command` (P1a), `build_search_where` split into named helpers (P1b), `Volume::online_map()` and `resolve_collection_ids()` extracted to deduplicate 20 call sites (P2), new `src/cli_output.rs` module consolidating three drifted copies of `format_size` + the `item_status(id, verb, elapsed)` pattern (P3b), and `web/routes.rs` split from 6,599 LOC into 13 domain submodules (348 LOC in `mod.rs`) (P3c). Tagging guide gains the "Thinking in facets" framework, worked examples for events and color, and the opt-in `event` / `color` top-level facets synced into the built-in default vocabulary. New `doc/qa-report.md` with the codebase analysis that drove the priorities.
- **v4.4.6**: New `maki tag split OLD NEW1 [NEW2...] [--keep]` command for one-to-many tag restructuring (e.g. `subject|event|wedding-jane-2025` → `event|wedding-jane-2025` + `subject|event|wedding` in one pass; or with `--keep`, additive / copy semantics). Matching split UI on the web tags page — a second button on leaf rows only (non-leaf rows get an alignment placeholder), opens a modal with dynamic target-input list, `Keep source` checkbox, Preview/Apply flow identical to rename. New "Tagging Quick Guide" A3 landscape poster at `doc/quickref/tagging.pdf` (printable wall reference with facet cards, decision helper, worked example, and tag-command cheat). Tagging-guide chapter gets a capstone illustration (SVG from maki-marketing rendered to PNG) showing one photo with nine tags from seven facets.
- **v4.4.7**: Small feature pack. New `tagcount:N` search filter counts *leaf* tags (intentional tags, not auto-expanded ancestors) via a denormalised `leaf_tag_count` column on `assets` (schema v7→v8, O(1) per row on large catalogues) — especially useful for restructuring (`tagcount:0` finds gaps, `tagcount:5+` surfaces noise). Path autocomplete on the filter bar: shell-style hierarchical completion with `↑`/`↓`/`Tab`/`Enter`/`Escape`, wildcard suppression, absolute-path auto-strip, volume scoping; backend aggregates in SQL (`GROUP BY` on a computed next-segment expression) so dense directories don't hide sparse siblings. `maki search --help` now embeds a categorised ~60-line filter reference via `long_help` (`-h` stays compact). Tagging-poster polish. Dep hygiene: `lofty` 0.23 → 0.24 (was yanked); transitive `core2` (unmaintained) dropped via `ravif` 0.13 / `image` 0.25.10 bump — `cargo deny check` clean again.
- **v4.4.8**: Tag vocabulary interchange with Lightroom / Capture One. `maki tag export-vocabulary --format text` writes a tab-indented keyword file (the format both tools import): full hierarchy preserved, XML entities decoded (`&amp;` → `&`), `,` and `;` replaced with spaces (both tools reject them as delimiters), whitespace collapsed. Sanitized tags are reported to stderr with a rename hint. The same normalization runs at ingest — `QueryEngine::tag` now auto-splits comma/semicolon-containing inputs at the single chokepoint used by CLI, web UI, and `auto-tag`, so AI-produced strings like `"red, gold, white"` can never land as one literal tag. Two maintenance bugs fixed: `maki sync --apply --remove-stale --path <dir>` now actually deletes stale recipe (XMP) records (previously it reported them and did nothing — only the media-file branch had the removal code); `maki cleanup --path/--volume` no longer mixes path-scoped counts with whole-catalog orphan counts (previews / embeddings / face files live in shared catalog directories, so the scan can't be meaningfully scoped — skip those passes when scope is narrowed and print a note pointing at a scope-free run).
- **v4.4.9**: Web import polish + workflow hints. The import dialog moves out of the volumes-page corner: it's now reachable from a global "Import" entry in the top nav with a pulsing-dot status badge whenever a job is running. Click while a job is in flight and the dialog **re-attaches** to the live SSE feed (last 100 events replayed, then live broadcast continues) — a page reload mid-import no longer loses the activity log. The dialog gains shell-style **path autocomplete** on the subfolder field via a new `GET /api/volumes/{id}/browse?prefix=&limit=&filter=&hidden=` endpoint with `canonicalize().starts_with(mount_canon)` security clamp (8 unit tests including symlink-escape), a **chip-based tag picker** matching the filter-bar UX (autocomplete from `/api/tags`, Enter/comma/click to add, Backspace to remove), full-width subfolder input, and a **scoped "Browse imported" link** (exact `id:` filter for ≤80 assets, volume+subfolder for larger batches — no more landing on the unfiltered browse page). Tier-A **workflow hints** added at the end of state-changing commands: `sync --apply --remove-stale` now hints at `cleanup` when locationless variants linger (the case the user hit IRL); `dedup --apply` does the same; `fix-roles --apply` and `auto-group --apply` hint `generate-previews --upgrade` since the best-preview variant changed; `generate-previews` lists which offline volumes blocked skips so the user knows what to mount; `import` (ai/pro) hints `embed`/`describe` when those phases weren't engaged; `rebuild-catalog` (ai) counts assets without embedding rows and assets unscanned for faces and hints the relevant follow-up commands. Same shape across all commands: a `Tip:` line at the end of the human-readable output naming the count, the action, and the command. Plus a CI fix for `cargo install cargo-about --features cli` — 0.9.0 gated the binary behind a non-default feature.
- **v4.4.10**: New **`maki status`** command — read-only catalog health overview that aggregates signals from cleanup, backup-status, schema-version, and AI/embedding stores into one prioritized "what needs attention" report. Sections: Catalog (schema version with migrate hint if stale, counts, storage), Cleanup (locationless variants + orphans on disk, all pointing at `cleanup --apply`), Pending work (XMP writebacks split by online/offline target volume, assets without embedding / face scan on AI builds), Backup coverage (at-risk count vs total at the configured `--min-copies` threshold), Volumes (sorted online-first with per-volume asset count + size + purpose). Every actionable line ends with a `→ command` suggestion so users don't consult docs to know the next step. `--json` emits a fully-typed `StatusReport`. Reuses the existing `service.cleanup` dry-run for orphan-on-disk counts (slow part — ~30s on 12k-asset catalogs); a one-line stderr prelude announces "Gathering catalog status…" so the user doesn't think the command hung. Also: web nav badge polling backed off — 4s during running imports, 30s when idle, paused entirely on hidden tabs (resumes on `visibilitychange` with an immediate refresh). Cuts background traffic by ~7× on an idle tab without sacrificing responsiveness during active imports.
- **v4.4.11**: Faceted sidebar becomes a **tag-strolling navigation surface**. Every facet row is now click-to-narrow — tags add chips (with the full disambiguated path), ratings/labels mirror their widgets, formats toggle the multi-select panel, volumes set the dropdown, years/geotagged append `date:YYYY` / `geotagged:1` to the search box. Tag rows render as an indented hierarchy (rebuilt client-side from the flat auto-expanded list returned by `/api/facets`) — the panel can show `event > festival > Holzkirchner Blues- und Jazztage > 2024 (12)` nested correctly under each parent. Section order rebalanced: Ratings → Labels → **Tags** → Years → Formats → Volumes → Geotagged (tags promoted because the curated taxonomy is most users' main filtering axis). Three new `window.*` helpers in `filter_bar_js` (`toggleFormatFilter`, `setVolumeFilterById`, `addQueryTerm`) keep the chip/widget logic centralized so the dispatcher just delegates. Keyboard accessible (Enter/Space) for every facet type. User-guide chapter 6 rewritten with click-action table and a worked exploration example (drilling into the Holzkirchner festival across years, using year/festival count discrepancies to spot inconsistently tagged photos).
- **v4.4.12**: Tag-page tree fix — children of tags whose name shares a prefix with flat siblings now render directly under their parent. The previous lexicographic full-path sort put `|` (0x7C) after ` ` (0x20), so a renamed child like `Bricking Bavaria|2011` ended up at the bottom of the prefix block (e.g. visually nested under `Bricking Bavaria 2025`'s subtree) instead of immediately under its actual parent. Fix: emit in tree pre-order — parent first, all descendants alphabetically by leaf segment, then next sibling at the same depth. The browse facet panel already used this approach correctly; the server-side `build_tag_tree` for the tags page now matches.
- **v4.4.13**: Tag-management feature pack and tag-page semantics overhaul. New **`maki tag delete <TAG> [--apply]`** — completes the rename/split/delete family with the same dry-run-by-default flow, `=`/`/`/`^` markers, cascading-by-default + leaf-only opt-out, and orphan-ancestor cleanup. Web UI gains a trash button on every tag row plus a Preview→Apply modal with hover-tinted destructive accent; backend at `POST /api/tag/delete`. Tag-page **count semantics** rewritten: the previous parenthesised number was nonsense (own_count + sum of descendants, double-counting because of auto-expansion) — replaced with a `(N as leaf)` count that surfaces "assets tagged at exactly this level with no deeper child", clickable to land on the leaf-only-filtered browse page. Hidden when zero or equal to the headline so cleanly-tagged hierarchies show one number. Browse-page **count-delta hints** next to the result count: "X more in stacks", "X more without default filter" — clickable to flip the corresponding URL flag, only shown when each delta is non-zero. **Facet sidebar tag list** lifted from a top-30 cap to 5000 (real catalogues mid-restructure are around 4500 distinct tags) — fixes missing-tag bug where lower-frequency co-occurring tags were silently truncated, and the knock-on tree-rendering bug where surviving descendants got synthetic count-0 parents. **Split modal keyboard flow** matches rename: Enter on a non-last target advances to the next row, Enter on the last row submits. Rename + split modals now share one `attachTagAutocomplete` helper (autocomplete suggestions + ↑/↓/Enter/Tab/Esc) — fixing the missing autocomplete on split target inputs. The `htmx:afterSwap` handler now syncs the stack-collapse JS state from the URL after every swap, so links that flip `&stacks=` (like the new "X more in stacks" hint) leave the toggle button in the correct visual state instead of requiring two clicks to flip back.
- **v4.4.14**: Live progress for every long-running web operation. New generic **`JobRegistry`** (in `src/web/jobs.rs`) lifts the bespoke per-route SSE + ring buffer + atomic-counters + re-attach plumbing out of the import job into one place; all four batch endpoints (`embed`, `auto-tag`, `detect-faces`, `describe`) now POST → `{job_id}` and emit per-asset progress through the same broadcast/snapshot pipeline. A reusable **progress toast** mounted globally from base.html (`window.makiJob.watch(jobId, label, {onDone})`) renders "X / Y done — status (asset)" lines while the job runs, then a summary line built from whatever counters the terminal event carries (auto-dismisses on success, sticks on error). Import dialog gains a **Minimize to toast** button: hand the running import off to the toast, close the modal, keep the job running unchanged on the server. New endpoints: `GET /api/jobs` (snapshot for nav badge), `GET /api/jobs/{id}` (single status), `GET /api/jobs/{id}/progress` (SSE) — replace the import-specific status/progress routes. Plus the **post-import embed and describe phases** that lived in CLI now wire into the web import dialog with two new checkboxes (gated by `/api/build-info` so they hide on builds without `ai`/`pro`); `[import] embeddings`/`[import] descriptions` config defaults honored when the request omits the field. Standalone **`Embed` button on browse toolbar and asset detail** for users who want similarity coverage without auto-tag side effects (`POST /api/batch/embed`, `POST /api/asset/{id}/embed`). And **`maki tag fix-unicode`** — collapse NFC/NFD duplicate tags caused by macOS NFD vs XMP NFC encoding drift. Same dry-run-by-default rhythm as `fix-dates` / `fix-roles`; write-path canonicalisation in `tag_input_to_storage` prevents new mismatches. `AssetService::embed_assets` extracted to dedupe ~150 LOC across `maki embed`, post-import phase, and the new web batch endpoints.
- **v4.4.15**: Maintenance release — entirely internal restructuring driven by a fresh QA report. **Every large file split** along its natural cleavage planes via multi-file `impl` blocks: `catalog.rs` 9200 → 4524 LOC across 17 submodules, `asset_service.rs` 8886 → 2759 across 12 submodules, `query.rs` 6820 → 6028 with the parsing layer extracted to `query/parse.rs`, `web/routes/ai.rs` 1614 split into 5 domain submodules. **`main.rs` 9725 → 2797 LOC**: 40 command handlers extracted into `run_X_command` functions and moved to a new `src/commands.rs`; `run_command`'s match shrinks from 5921 → 859 LOC of one-line dispatch arms. **`AssetService::import_workflow`** (in `asset_service/workflow.rs`) lifts the orchestration that lived between input parsing and the kernel call — profile resolution, filter assembly, volume resolution, tag merging, post-import auto-group with neighborhood scan + preview upgrade, post-import embed phase, post-import describe phase. CLI handler shrinks 454 → 234 LOC; web handler 446 → 327. The web inherits the CLI's auto-group neighborhood scan + post-group preview upgrade for free (it had quietly drifted off both). `build_search_where` further decomposed (357 → 205 LOC via 6 new per-filter helpers); `parse_search_query` switched to four lookup tables (242 → 186 LOC). `config::load_config()` collapses 27 paired `find_catalog_root() + CatalogConfig::load()` call sites; `config::resolve_model_dir()` deduplicates `~/`-expansion across CLI and web; `web::routes::resolve_asset_id_or_err()` and `spawn_catalog_blocking()` lift two more copy-paste patterns. 29 source files gained `//!` module docs; 17 large templates gained leading purpose comments. Tests unchanged from v4.4.14 (779 + 249 standard, 886 + 273 pro) — the refactor is structural and behavior-preserving.
- **v4.5.0**: Behaviour & UX release. **XMP writeback rework**: `[writeback] enabled` now governs only *automatic* flush on every edit; tracking (`pending_writeback`) is unconditional and `maki writeback` is the explicit manual flush that runs whether or not the flag is set — so users can keep auto-flush off as a safety net while still pushing staged metadata onto disk on demand. **`maki writeback --mirror-tags`** (requires `--all`) reconciles XMP `dc:subject` + `lr:hierarchicalSubject` against the catalog and removes stale entries — fixes the additive-only flush bug where tag renames/splits/deletes left the OLD keyword stranded on disk alongside the new one. **Browse `Shift-Cmd-A`** selects all assets matching the current filter across pages via a new `/api/all-ids` endpoint and a confirmation modal (replace/add radios when an existing selection is non-empty). **Tags page click count alignment**: row clicks now use `=^` and `=^/` markers so the click result population exactly equals the displayed row count; the tag-filter parser learned to combine `=` and `/` (`=/foo` = whole-path AND leaf-only). **Tag autocomplete**: middle-of-hierarchy matches no longer hidden by their descendants; clicking the dimmed prefix span drills into that level. **`maki tag export-vocabulary --counts`** + nested JSON format. Plus: filter-bar path autocomplete cap raised 20 → 100; browse pagination clamps to last available page after destructive ops; two browser regressions from v4.4.15 template-comment refactor fixed. Tests: 782 + 249 standard, 889 + 276 pro (up from 779 + 249 / 886 + 273).
- **v4.5.1**: Web-UI release. New **Maintain dialog** in the top nav (parallel to Import) exposes the long-running maintenance commands to the web UI: tabbed modal with **Writeback** (volume+query scope, `--all`, `--mirror-tags`, `--dry-run`), **Sync metadata** (volume scope, `--media`, `--dry-run`, conflict report in summary), and **Verify** (volume scope, max-age-days threshold). Each tab POSTs to a new `/api/maintain/<op>` endpoint that returns `{job_id}` immediately and streams per-file progress through the existing `JobRegistry` SSE pipeline; the standard progress toast renders live counters and final summary. JobKind enum gained `Writeback`/`SyncMetadata`/`Verify` variants; the toast learned the new summary counters. At-most-one-job-per-kind enforced server-side (409 on conflict); different kinds run in parallel. Five top-level nav entries (Stats, Analytics, Backup, Volumes, Duplicates) collapsed into a **Catalog ▾ dropdown** to keep the nav bar tidy now that Maintain joined Import. Dropdown is keyboard- and screen-reader-accessible. Plus a checkbox-layout fix in the new dialog (the inherited `.import-modal label { flex-direction: column }` rule leaked into checkbox labels and stacked each child onto its own line; explicit `flex-direction: row` reset). Tests unchanged: 782 + 249 standard, 889 + 276 pro.
- **v4.5.2**: Web-UI release. Maintain dialog grows from 3 tabs to **7**: new **Previews** (volume scope, `--smart`, `--upgrade`, `--force`), **Sync** (file-layer reconciliation: required volume picker, optional volume-relative subpath with filesystem autocomplete, `--apply` + `--remove-stale`), **Refresh** (re-read sidecar XMP, `--media`, `--dry-run`), **Cleanup** (orphan removal: volume + path-prefix scope with autocomplete, `--apply`). JobKind enum gained four new variants; shared toast learned 10 new summary counters (`generated`, `upgraded`, `refreshed`, `moved`, `new_files`, `missing`, `stale_removed`, `removed_*` for cleanup). Modal width raised 500 → 750 px (scoped override) so seven tab labels fit on a single row. Path autocomplete on Sync and Cleanup mirrors the import dialog's UX (↑/↓/Tab/Enter to drill, Esc to dismiss, 120 ms debounce); volume label → ID resolution via a cached `volumesByLabel` map. Subpath canonicalize-and-prefix-checked against the volume mount on the server so `..` can't escape the volume. Tags page gets a one-click **Export vocabulary…** button next to the H1; opens a small modal with format radio (YAML / Keyword text / JSON) + counts/prune/default checkboxes; Download navigates to `GET /api/tags/export-vocabulary?…` which streams back the file with `Content-Disposition: attachment`. Output is byte-identical to the CLI command. Generate-previews has no engine method (CLI handler does the work directly), so the web handler replicates the catalog-mode loop in maintain.rs (~80 LOC); a future shared `AssetService::generate_previews_for_assets` helper is queued. Tests unchanged: 782 + 249 standard, 889 + 276 pro.
- **v4.5.3**: Bug-fix patch. Four web-UI fixes surfaced by real-world tag-cleanup work. **Saved searches**: `to_url_params` previously emitted URL params only for `q`, `type`, `tag`, `format`, `label`, `rating`, `sort`. Anything else (path, volume, collection, person, niche filters like camera/iso/tagcount/geo, exclude variants, etc.) was silently dropped — clicking a chip with `path:Pictures/2026/05/` reloaded the browse page with no path filter. Two-pass fix: (1) emit dedicated URL params for widget-backed filters; (2) tokenize the raw query, drop the consumed tokens, dump the remainder into `q=`. Single-value URL params absorb only the first occurrence so `format:jpg format:tiff` keeps the second in `q=`; multi-value (`tag`, `person`) consume all and emit comma-joined; negations (`-tag:rejected`) always stay in q=; whitespace values get re-quoted before joining; `label:none` round-trips via the `label=none` sentinel. Made `query::tokenize_query` `pub`. **Browse → detail navigation**: cross-page Next handler never updated `maki-browse-page`, so once the user walked off the end of the concatenated browseIds list the boundary fetch re-appended the same page → duplicate IDs. Split into `page-min` / `page-max` so the prev and next boundaries track separate counters. **Import dialog log**: `PhaseStarted` events for `import` / `auto_group` phases fell through to the generic per-file else branch and rendered as "phase_started undefined" (no `file` field). Added a dedicated branch for `status === 'phase_started' || 'phase_skipped'` that renders `— import phase started —` etc. with a small `.import-log-phase` CSS class. Tests: 790 + 249 standard, 897 + 276 pro (eight new round-trip tests in saved_search).
- **v4.5.4**: Lightbox **slideshow mode**. Two new toolbar buttons (▶/▌▌ play-pause, ↻/→ loop toggle) plus three keyboard shortcuts: **Space** toggles play/pause; **`+`/`-`** while running bump the cadence ±1 s (clamped 1–60); a small "5s" speed badge flashes the current value. Auto-pauses on every deliberate user action — prev/next click, arrow-key navigation, rating change, label change, Escape. Cross-page advance: the slideshow walks the entire result set, not just the current 60-asset page; reaching the end of a page hooks into the existing `_onNavigateBeyond` callback so the host swaps in the next page's results via htmx and the lightbox reopens at index 0 with the timer still ticking. Loop-from-end-back-to-start: when loop is on AND we hit the last asset of the last page, browse.html's onNavigateBeyond queries the lightbox (`isSlideshowLooping()`/`isSlideshowRunning()`) and navigates to page 1 via URL-rewrite + `htmx.ajax` (replaces the old "click the nth-child pagination link" approach for robustness). Loop-off at the same boundary detects the no-progress case (same item id after `navigate(1)`) and stops the slideshow cleanly so it doesn't tick forever on a frozen view. New config in `[browse]`: `slideshow_seconds = 5` and `slideshow_loop = true`, surfaced to the lightbox JS via the existing `/api/build-info` endpoint (which gained two fields alongside the existing `{ai, pro}` keys). Runtime adjustments are session-scoped. Tests unchanged: 790 + 249 standard, 897 + 276 pro — slideshow is browser-side JS exercising the existing `navigate()` function.
- **v4.5.5**: Web **Settings dialog** — schema-driven `maki.toml` editor. Every `CatalogConfig` field derives `schemars::JsonSchema`; a client-side walker renders widgets by type (bool → checkbox, integer/float → number with `step="any"`, string → text/select, `Vec<String>` → comma-separated, struct → `<details>` section, `BTreeMap<String, T>` → one editable sub-section per existing key). Three endpoints: `GET /api/config`, `GET /api/config/schema`, `POST /api/config` (validated by serde round-trip, previous file backed up to `maki.toml.bak`). Restart-required pill on boot-time options + colour-coded toast on save. Adding/renaming hashmap keys (`import.profiles.<name>`, `vlm.model_config."<model>"`) stays manual — the schema can't constrain the legal key set. Plus: the **Maintain dialog** gains the same forms → progress → result phases the Import dialog already had (status line + last 50 log lines + Minimize-to-toast button while running; counter-list summary on completion); re-attaching to a running job opens the dialog in progress phase, not the toast. Terminal `done:true` invalidates the browse-side tag autocomplete cache so cleanup / sync ops don't leave stale taglists in flight. **Tag bulk mutations** (`rename` / `split` / `delete` / `fix-unicode`) tolerate missing-sidecar errors mid-loop instead of aborting — record on `errors: Vec<String>` on the result, continue the loop. **Config serialisation determinism**: every section now always emitted in declaration order (was `skip_serializing_if = "is_default_*"` at section level — saved a few lines on default catalogs but made the Settings dialog's "save" feel ambiguous and produced diff-noisy reorderings once one field in a previously-skipped section was touched). Config float fields `f32` → `f64` to round-trip cleanly through TOML (was producing `0.10000000149011612` for a stored 0.1). `BTreeMap` (not `HashMap`) for `import.profiles` and `vlm.model_config` so the saved file lists entries alphabetically rather than in randomised iteration order. Tests: 794 + 249 standard, 901 + 276 pro (four new config-round-trip regression tests on each flavour).
- **v4.5.6**: Writeback bugfix patch. `maki writeback` was clearing the YAML sidecar's `pending_writeback` flag on recipes it had actually skipped (offline volume, missing file), while the SQLite-side clear inside the per-recipe loop correctly skipped via early `continue` — the two layers diverged. Practical impact: a subsequent `maki rebuild-catalog` (which rebuilds from YAML, the source of truth) would silently lose the staged edits. Fix tracks per-recipe completion in a `cleared_recipe_ids: HashSet<String>` populated only on the success path, and has the sidecar-save loop honour that set instead of the broader `recipe_entries`. Skipped recipes now keep `pending_writeback: true` in both layers so the next writeback picks them up when the volume comes back online. Audit while in there confirmed the inline writeback `_inner` paths (rating / tag / description / label) were already per-recipe-safe via `mark_recipe_pending` / `clear_recipe_pending` helpers; `[writeback] enabled = false` semantics from v4.5.0 still hold (gate inside `_inner`, none in `writeback_process` so manual flush always runs); `--all`, `--mirror-tags`, and the web `POST /api/maintain/writeback` route all flow through the same `writeback_process` and are covered by the same fix. New regression test `writeback_preserves_pending_when_volume_offline` (registers a removable volume in a sibling tempdir, edits, renames the mount to take it offline, runs writeback, restores the mount, asserts both `maki status` and the YAML sidecar still report pending). Verified the test FAILS without the fix. Tests: 794 + 249 standard, 901 + 277 pro (+1 regression).

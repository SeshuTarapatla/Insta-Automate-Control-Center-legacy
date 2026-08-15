# Decision log

Newest first. Each entry records what was chosen, what was rejected, and why — so a future
session can tell a settled question from an open one.

---

## 2026-08-11 — Live bug: gender_valid/gender_invalid stuck at 0 in the Library screen (D126)

### D126 · Library counts get a periodic-reseed safety net alongside the existing touch-driven watcher

**Found live:** you reported the Library screen showing 0 for `gender_valid`/`gender_invalid`
despite one real entity (189 and 286 files respectively) sitting in each on disk. Confirmed via
direct agent API calls (not the GUI, per rule 5) that `GET /api/library/images` — which reads disk
live — saw the real files correctly, while `GET /api/library/folders`/`entities` — which reads
`LibraryCounts`' cache — reported 0. Root-caused by writing harmless probe files into several
library folders and watching whether the cache picked them up: `scanned` and `scraped` updated
within seconds as designed; `gender_valid`/`gender_invalid` did not update at all, for either a
brand-new subdirectory or an existing untracked one, even after 10+ seconds. Not a coalesced-or-
dropped single event (CP 5.1's `touch()` design already tolerates that — the next real touch of the
same pair self-corrects it) but the underlying watch for those two directories going completely
silent, permanently, while sibling folders kept working. The likely trigger: `entity_classify`
(`Insta-Automate/tasks/ollama.py`) moves a whole batch of files into both directories in one tight
loop — that burst of rapid renames is a known way to overflow Windows' `ReadDirectoryChangesW`
change-notification buffer for the specific directory being hammered, and `watchfiles`' Windows
backend does not appear to self-heal that subtree afterward.

**Chosen:** `library/watcher.py`'s `watch_library` now runs the existing touch-driven `awatch` loop
(renamed `_watch_changes`, unchanged logic) alongside a new `_periodic_reseed` task — every 5
minutes (`_RESEED_INTERVAL_SECONDS`, overridable per-call for tests), it calls `counts.seed()`
again in full, diffs the result against what was cached, and — only on real drift — publishes a
`library.changes` event so the app's existing full-refetch-on-any-event listener
(`library_controller.dart`'s `_touchesLibraryChanges`) picks it up with no client-side change
needed. **Rejected:** trying to detect and specifically recover from the Windows buffer-overflow
condition itself — `seed()` is already measured at ~15ms over the real 7,655-file `IA_DIR` (D35),
so a plain interval is both simpler and more robust than chasing a platform-specific failure mode
that may not be the only way a watch can go silent.

**Verified:** `agent/tests/test_library.py` grew from 82 to 87 checks — two new cases simulate a
dead watch by writing straight to disk (bypassing `counts.touch()` the way a real dead watch
would) and confirm the periodic reseed both republishes the correct total and repairs the cache
itself, plus a case confirming no spurious publish when nothing actually drifted. All 87 pass.
Live-verified against the real agent: restarted (`taskkill /F /IM ia-agent.exe`, the launcher
respawned it in ~8s, all three supervised services confirmed still `supervised`/`adopted` — not
`external` — across the restart, same as every prior restart in this project's history) —
`GET /api/library/folders` immediately showed the real counts (`gender_valid: 189/1`,
`gender_invalid: 286/1`), fixing the reported symptom. The periodic-reseed path itself (catching a
*future* silent watch failure without a restart) is proven at the unit level via the shortened-
interval test above, not re-triggered live against a real Windows buffer overflow — that would mean
deliberately reproducing a race, not something worth forcing against real pipeline data.

**Scope note:** this is an agent-side fix, not v2 work — v2 is `app/`-only per CLAUDE.md's own
scope boundary, and nothing here touches `app/`. Recorded here rather than folded into any V2
checkpoint.

---

## 2026-08-11 — V2.13.1/V2.13.2/V2.13.3 accepted by your own call; V2.14's motion/accessibility half built (D125)

### D125 · V2.13 accepted without a separate live pass; V2.14 split into motion/accessibility (done) and release (not started)

**Chosen:** you confirmed V2.13.1 (Device identity), V2.13.2 (Library review mode refinements) and
V2.13.3 (Dashboard & shell fixes) as done and tested by your own explicit call, the same standing
precedent as CP 7.3's partial-pass acceptance and Phase 2/5's outright acceptances — not a Claude-run
test, since rule 5 forbids that categorically. V2.13.1's device-model-caching half stays genuinely
unverified against a real device (the phone is still disconnected, D116) but that's now the user's
call to accept, not a gate Claude can hold open.

**V2.14 was then split rather than attempted whole.** PLAN_V2.md's own V2.14 scope is three
unrelated pieces — motion audit, accessibility floor, and the release mechanics (version bump, tag,
ARCHITECTURE.md update, a full live pass in three themes). Only the first two make sense for Claude
to build blind: they're auditable from source (DESIGN_SYSTEM §1.9/§6's own checklists) and testable
headless (`flutter test`), where release's own checkpoint test is explicitly "a full pass over every
screen in at least three themes... at the real window size" — exactly the live-driving rule 5
forbids. **Release stays unstarted**, including the `pubspec.yaml` version bump and the `v2.0.0` tag
— PLAN_V2.md is explicit those land at the very end, not before its own checkpoint test, and rule 4
already forbids building ahead of an untested checkpoint once; doing the same to V2.14's own last
third would repeat exactly what that rule exists to prevent.

**Motion audit.** `MotionTokens`/`motion.reduced` (with a real Settings → Appearance override,
`ReduceMotionSetting.always/never/auto`, reading `MediaQuery.disableAnimations` under `auto`) was
already fully wired from V2.4 — nothing to add there. The actual gap: six `ScrollController.animateTo`/
`Scrollable.ensureVisible` calls across `library_grid.dart`, `review_page.dart`, `log_console.dart`,
`classify_surface.dart`, `limits_tab.dart` and `command_palette.dart` used bare hardcoded
`Duration`s that never checked `tokens.motion.reduced` at all — every one now resolves to
`Duration.zero` (an instant jump, not a skipped scroll — `ScrollPosition.animateTo` already treats
zero as `jumpTo` internally) under reduced motion. `FunnelChart`'s draw-in and `_Shimmer`'s loading
breathe were already correctly gated; `StatusDot`'s pulse stays deliberately untouched per
DESIGN_SYSTEM §1.9's own "anything that repeats forever must mean still in progress" exemption.

**Accessibility floor.** Four real gaps, not a rewrite: the title bar's minimize/maximize/close
buttons (`shell/title_bar.dart`'s `_WindowButton`) had no `tooltip` at all — a screen-reader user had
no way to know what they did; fixed with per-action tooltips. `AppTooltip`'s `rich: true` path (the
D93 flow mechanism/gate tooltip and six other call sites) builds its message as a `richMessage`
`WidgetSpan`, which Flutter's `Tooltip` can't auto-stringify into a `Semantics` label the way it does
for a plain `message:` string — fixed once at the shared component with an explicit `Semantics(label:)`
wrap, covering every `rich: true` call site instead of seven individual patches. The library grid's
image tiles (`library_tile.dart`) had a bare `GestureDetector` with no `MouseRegion` cursor, unlike
every other clickable surface in the app (`AppPanel`, `AppMenu`'s trigger, the resize handle,
`_ThemeCard`, `surface_common.dart`'s result cards all already set one) — fixed with
`SystemMouseCursors.click`. The search field's clear `IconButton` (`ui/fields.dart`) had no tooltip —
fixed. And `notification_center.dart`'s bell/panel — an `Overlay`/`CompositedTransformFollower`
popover, not a `showDialog` route, so it gets none of `showDialog`'s free focus trap/restore — had
neither: Tab could escape into whatever sat behind the translucent barrier, and closing left focus
wherever it happened to land rather than back on the bell. Fixed with a `FocusScope` wrapping the
panel (`Shortcuts`/`Actions` deliberately wrap *outside* the `FocusScope`, not inside — they only
catch a key event whose focused target is a descendant of their own subtree, and the scope itself
becomes that target once nothing more specific inside claims it) and an explicit `Esc` binding.
**Getting the focus-claim timing right took two wrong turns, both real, both caught by a new
regression test before being trusted, not assumed correct:** a `FocusScopeNode.requestFocus()`
called from `_NotificationCenterState._open()` right after `overlay.insert()` fired too early — that
callback runs at the end of whatever frame is *already in flight*, not the later frame that actually
builds the overlay's content, so the request landed on a scope with no attached widget yet and was
silently lost (confirmed via `WidgetsBinding.instance.focusManager.primaryFocus` in the failing test —
it stayed on `MaterialApp`'s own root modal scope). Switching to `FocusScope`'s own `autofocus: true`
didn't fix it either: `autofocus` only claims focus when its *enclosing* scope has no focused child
yet, and by the time the panel is inserted, Overlay's shared ancestor scope already resolved one
during initial app construction — the same "autofocus is conditional, an explicit request isn't"
class of bug D123 already hit once for review mode's own autofocus. **The actual fix**: schedule the
`requestFocus()` call from inside `_NotificationPanelState.initState()` itself, not from the caller —
a callback posted from within the widget being mounted necessarily waits for the frame *after that
widget's own construction*, which is the first moment its `FocusScope` context actually resolves to
something real, mirroring D123's own `_LibraryReviewPageState.initState()` fix exactly. New
`notification_center_layout_test.dart` case (`Esc closes it and returns focus to the bell`) failed
against both wrong attempts before passing against the real fix.

**Not attempted, deliberately:** a full manual focus-order/traversal audit across every screen (no
other genuine gaps found by source inspection — `showDialog`'s modal routes already trap/restore
focus for every real dialog in the app, `IconAction`/`_NavTile`'s collapsed tooltip/`_CollapseToggle`
already had both tooltip and an implicit `Semantics` from `Tooltip`), and the plan's own "Performance
check: the library grid scrolling 7,655 thumbnails, the log console at a few thousand lines, Mica
compositing while the terminal streams" — this needs the real running app under real load, which
rule 5 puts squarely in your hands, not something source-level review can stand in for.

**Verified:** `flutter analyze` clean. `flutter test` 233 total / 232 passing — the same
`shell_layout_test.dart` `rail expanded` failure D114 first found, reconfirmed pre-existing and
unrelated via `git stash` on the unmodified branch tip before any of this session's edits were made
(same lineage as every prior session's reconfirmation). `flutter build windows --debug` succeeds.
Built, the stale prior instance (running since the previous session, 2026-08-10) killed, and started
fresh for you per rule 5.

**Checkpoint test (yours, before this can be called done):** confirm Escape closes the notification
panel and returns focus to the bell (`Tab` afterward should move on from the bell, not re-enter the
panel); confirm Tab inside an open notification panel never reaches something behind it; confirm the
title bar's minimize/maximize/close buttons show a tooltip on hover; confirm the library grid's image
tiles show a pointer/click cursor on hover; confirm turning on Windows' "Show animations: Off" (or
Settings → Appearance → Reduce motion → Always) makes keyboard-driven scrolling in the library grid,
review mode's filmstrip, and the log console search jump instantly instead of animating.

## 2026-08-10 — V2.13.3 (Dashboard & shell fixes) built, app-only, awaiting your checkpoint test (D124)

### D124 · Caps tile stops trusting a frozen heartbeat; nav rail toggle's whole row is now the hit target; StatusChip bumped and made ellipsis-safe; "This machine" → "Host"

**Finding #1 — the frozen caps tile, root-caused rather than guessed.** PLAN_V2.md flagged two
hypotheses and asked to start with the scheduler's day-counter/heartbeat logic. Read directly:
`Insta-Automate/models/scan.py`/`scrape.py`/`follow.py`'s `.fetch(session)` always queries by
`Timestamp().date()` (today), returning a fresh zero-valued row when none exists yet — so
`controllers/prefect.py::_today()` is *not* lazily gated on a flow's first trigger of the day;
hypothesis (a) as originally stated doesn't hold while the scheduler pod is actually heartbeating.
The real gap is earlier in the same file: `heartbeat_loop()` is only ever started from inside
`serve()`, *after* `await wait_for_device(self.tl)` resolves — with the phone disconnected
indefinitely (D116), that await never returns, so the heartbeat loop never starts at all, and the
agent's `SchedulerMirror._flows` (`agent/src/ia_agent/scheduler.py`) keeps whatever it last held
(a prior day's real numbers) forever. `online()` does flip to `false` after `STALE_AFTER` (15s),
but nothing on the app side was reading that flag before trusting `flows`. Fixing the actual root
cause (decoupling the heartbeat loop from device connection) is a pipeline change, out of scope
per the standing v2 `app/`-only boundary — no exception was raised for it here. Fixed app-side,
defensively and correctly for both hypotheses at once: `overview_page.dart`'s `_CapsTile` now
passes `liveFlows` only when `SchedulerSnapshot.online` is true (a stopped heartbeat no longer
masquerades as current data), and `caps_tile.dart`'s burndown fallback now checks the fetched
snapshot's last day against the actual wall-clock date (`_todayKey()`) before treating it as
"today" — a genuinely new day with no live data reads as 0, not as whichever day the once-per-
session snapshot happened to end on. New `test/caps_tile_test.dart` (3 checks, `CapsTile` tested
in isolation) — the "falls back to 0" case was confirmed to actually fail against the pre-fix
`_CapBar` (asserted `5/300` where the fix now shows `0/300`) before being trusted.

**Finding #2 — the nav rail collapse toggle's whole row is now the hit target.**
`shell/nav_rail.dart`'s `_CollapseToggle` was a small `IconButton` that relocates when the rail
expands/collapses, so every click after the first needed the cursor to chase it. Rebuilt as an
`InkWell` wrapping the full-width row (matching `_NavTile`'s own tappable-row shape above it),
with the icon still visually anchored where it was (right-aligned when expanded, centered when
collapsed) via `Align` rather than driving the hit area. New `shell_layout_test.dart` case taps
the row's far-left edge — deliberately away from the icon — and confirms it still toggles;
confirmed failing against the pre-fix `IconButton`-only version first.

**Finding #3 — `StatusChip` bumped, and made to degrade instead of overflow.** `ui/status.dart`'s
`StatusChip` moved from `labelSmall` (10.5px) to `labelMedium` (12px) with proportionally larger
padding — one shared-component change (COMPONENTS.md's established pattern, V2.2/V2.7/V2.9), so
Live's counters and the Dependencies table both read larger without a per-call-site tweak.
`run_summary.dart`'s private `_CounterChip` (mirrors `StatusChip`'s shape locally rather than
widening the shared one, since every other call site wants a plain label and this one wants an
`AnimatedCounter`) was bumped to match — its label word had been `labelSmall` even though the
count beside it already rendered at `labelMedium`, an internal size mismatch on top of the same
complaint. **A real regression surfaced immediately by the existing test suite, not found live**:
`service_tile.dart`'s origin badge ("external"/"adopted", already documented in its own comment as
tightly fit at the 300px card floor) started overflowing by 8.7px under the larger chip. Root
cause: `StatusChip`'s `Text` had no `overflow`/`maxLines` at all, so a `Flexible` ancestor had
nothing to shrink — and a single unbreakable word like "adopted" can't wrap to satisfy a tighter
allocation, so Flutter reports a hard `RenderFlex` overflow instead of a soft truncation. Fixed at
the shared component (`maxLines: 1, overflow: TextOverflow.ellipsis`, wrapped in an internal
`Flexible`) rather than special-cased in `service_tile.dart` — any other tightly-fit call site is
covered the same way now. New `test/ui/status_test.dart` case (a `StatusChip` forced into a 40px
`Flexible`) confirmed failing with the exact overflow before the fix, passing after.

**Finding #4 — one-line rename.** `core/dependency_models.dart:39`'s `DependencyGroup.host.label`:
`'This machine'` → `'Host'`.

**Verified:** `flutter analyze` clean. `flutter test` 232 total / 231 passing — the one
`shell_layout_test.dart` failure (`AppShell … rail expanded`, an icon-size assertion unrelated to
anything touched this session) reconfirmed pre-existing via `git stash` on the exact same assertion
and message, matching D114's original finding. `flutter build windows --debug` succeeds. Built,
stale prior instance killed, and started fresh for you per rule 5.

**Same-session fix, from your immediate live retest: the toggle's icon wasn't actually centered in
either state.** The expanded case was deliberately right-aligned by design (`Alignment.centerRight`
+ an 8px right `Padding`) to keep the icon where it visually sat before this checkpoint — but that
same right padding stayed on in the collapsed case too, where the alignment *was* `Alignment.center`,
so the padded box (icon + 8px of empty space on its right) is what got centered, leaving the icon
itself sitting ~4px left of true center. Fixed by dropping the right-alignment scheme entirely —
the icon is now plainly `Center`ed with no extra padding, correct in both states, matching what you
actually asked for ("properly aligned to the center in both cases") rather than the original
"keep it where it visually was when expanded" read. `flutter analyze` clean, `flutter test`
unchanged (the row-wide tap test doesn't assert icon position, only that the row responds).
Rebuilt, prior instance killed, restarted fresh for you.

**Not yet checkpoint-tested live** — this session's own defensive fix for Finding #1 can't be
exercised against a real day rollover with the phone still disconnected (D116); the checkpoint
test itself (PLAN_V2.md's own "stop every flow, let a day roll over (or simulate it)") is still
yours to run, alongside a plain look at the nav rail toggle, Live/Dependencies status labels, and
the Dependencies "Host" rename.

---

## 2026-08-10 — V2.13.2 (Library review mode refinements) built, app-only, awaiting your checkpoint test (D123)

### D123 · Review's nav entry gets the real stage-priority list; Apply runs on decided images only via move+delete; review mode stays embedded instead of full-screen

**Finding #1 fixed — the nav rail's Review entry can now land on `gender_invalid`.**
`shell/nav_rail.dart`'s `openReview()` picked `curationFolders.first` unconditionally —
`curationFolders` (`overview/curation_tile.dart`) is `['gender_valid', 'scraped']`,
deliberately narrowed for Overview's own "needs attention" surface (D115) and left untouched
here on purpose. New `review_page.dart::openReviewModeForFirstBacklog(folderPriority)` walks
`libraryStageGroups`' own YOUR REVIEW group (`gender_invalid → gender_valid → scraped`, the
real stage order, already the one source of truth D115's last addendum established) and picks
the first folder with a nonzero backlog, then defers to the existing
`openReviewModeForFolder` to pick that folder's first entity with a real backlog. The nav
rail's own `reviewCount` badge and its Review-sub-item "selected" highlight were widened to the
same three-folder list for the same reason — a badge reading only two of the three real
review-stage folders would have been inconsistent with an entry point that can now land on all
three. `curationFolders` itself, and every surface D115 deliberately narrowed it for (the
Overview hero tile, the curation tile's own badge and "Review →" button, the command palette's
two explicit per-folder `Review: gender_valid`/`Review: scraped` commands), is untouched — the
plan's own fix explicitly scoped this to "the nav rail's Review entry," not every consumer of
`curationFolders`.

**Finding #2 fixed — Apply runs on whatever's actually been decided, not the whole loaded set.**
`review_page.dart`'s old `canApply` required `!hasMore && images.every(decided)` before Apply
would run at all, because the only mechanism it had — the toolbar's whole-directory
`applyLibrarySelection` (`POST /api/library/apply`, reads the folder fresh and trashes
*everything not selected*) — would otherwise trash every image past wherever review stopped,
D90's mobile bug in a new shape. New `library_toolbar.dart::applyReviewDecisions` replaces that
call with D90's own explicit-pair primitives instead: kept images move via
`POST /api/library/move` (a no-op when the folder's configured target is itself — nothing to
move, the image stays where it is) and discarded images delete via the existing
`POST /api/library/delete`. Neither call can ever name an image the reviewer hasn't explicitly
decided, so `canApply` is now just `_decisions.isNotEmpty` — no `hasMore` gate needed, since
there's no "everything else" left to accidentally sweep up. A decided-and-kept image whose
target is identity (stays in the same folder) keeps its green mark in local state after Apply,
since nothing actually happened to it on disk; a moved or deleted image's decision is dropped,
since re-opening the same folder later won't show it again anyway. Apply **no longer
auto-closes review mode** on success — the old behavior assumed finishing meant the whole
folder was done; a partial apply is now the expected, common case, and closing on every chunk
would eject the reviewer mid-session. New `MoveResult`
(`core/library_models.dart`) and `LibraryImagesController.move()` mirror the existing
`ApplyResult`/`apply()` shape.

**Finding #3 fixed — review mode is confined to the Library page's own content area.**
D115 built review mode as `Navigator.push(fullscreenDialog: true)` on the *root* navigator,
covering the title bar and nav rail entirely, matching SCREENS.md §5b's mockup at the time. The
user now wants the nav rail reachable while reviewing — re-architected as a plain
`libraryReviewingProvider` bool (`library_controller.dart`) that `LibraryPage.build()` checks:
when true, it renders `LibraryReviewPage` directly in place of its normal three-pane
folder/entity/grid view (keyed on `folder`/`entity` so re-triggering the nav rail's Review
entry mid-session for a different backlog always starts with fresh decisions rather than
Flutter reusing the previous review's `State`), leaving `AppShell`'s title bar and nav rail
untouched as siblings above/beside it. `openReviewMode` (every entry point: the toolbar's
Review button, the `R` shortcut, the nav rail, Flows' ⚑ edges, the command palette) is now
synchronous and context-free — it sets folder/entity/nav-index and flips the flag, nothing to
await. `LibraryReviewPage`'s own Esc/close-button/Apply-completion handlers, which used to call
`Navigator.of(context).pop()`, now call the same flag off instead — popping the app's *root*
Navigator (there is no longer a pushed route to pop) would have hit "cannot pop the last
route." The double-click lightbox (`LibraryLightboxPage`, SCREENS.md §5c) is untouched — a
different, browse-only feature not in this checkpoint's scope, still a real pushed route.

**Verified.** `flutter analyze` clean, `flutter test` 226 total / 225 passing (`review_mode_test.dart`
rewritten for the embedded harness and the new partial-apply behavior — a `Consumer` watching
`libraryReviewingProvider` stands in for `LibraryPage`'s real swap, the same way the old suite
stood in for a pushed route; `flows_layout_test.dart`'s ⚑-edge test updated to assert the
provider state directly rather than a rendered "REVIEW" string, since tapping the edge no
longer renders anything in that test's bare `PipelineEdge`-only tree; the one failure is
D114's same pre-existing, unrelated `shell_layout_test.dart` issue, reconfirmed via `git stash`
on the branch tip before writing any code here). `flutter build windows --debug` succeeds.
Built and started for you per rule 5.

**Same-session fix, found by your immediate live retest: every review-mode keyboard shortcut
was dead on arrival.** Root cause was the embedding change itself (finding #3 above), not the
keyboard map — `LibraryReviewPage`'s `Focus(autofocus: true)` reliably won focus back when D115
pushed it as its own `Navigator` route, because pushing a route is one of the few places
Flutter *actively* moves focus to the new content; `autofocus` on its own only claims focus
when the enclosing scope has no focused child *at all*, and once this widget is instead just
swapped in in place of `LibraryPage`'s content, whatever was focused at the moment "Review" was
clicked (a toolbar button, a nav rail tile) was still the scope's recorded focused child when
the new widget mounted, so autofocus silently did nothing and every key event had nowhere
useful to go. `library_grid.dart` already carries the same lesson in its own code — it never
trusts autofocus either, requiring an explicit per-tile `onRequestFocus: _focusNode.requestFocus`
tap before its own keyboard shortcuts work. Fixed by having `_LibraryReviewPageState.initState()`
explicitly call `_focusNode.requestFocus()` in a post-frame callback (after the node is actually
attached), rather than relying on `autofocus` alone. `flutter analyze` clean,
`flutter test test/review_mode_test.dart` 6/6 (unchanged by this fix — the widget-test harness's
`tester.sendKeyEvent` didn't reproduce the bug, so this was only caught by your real, running
app). Rebuilt and restarted for you. **Still awaiting your full checkpoint test.**

---

## 2026-08-10 — V2.13.1 (Device identity) built, agent-side + app-side, awaiting your checkpoint test (D122)

### D122 · Cached serial→model map + a pinned-serial override, both agent-side; a new Settings device-pin card on top

**What shipped, agent side (`agent/`).** New `ia_agent/device_settings.py` — a `%LOCALAPPDATA%
\ia-agent\device.json` settings file, same atomic-write/machine-local shape as
`library/settings.py` (D12's precedent again): a `pinned_serial` (`None` by default) and a
`model_cache` (`{serial: model}`). Its `resolve_model(serial, live_lookup)` is the actual fix
for finding #1 — a live adb read that succeeds updates the cache and returns the fresh model;
a live read that fails (disconnected, adb down) falls back to whatever's cached for that
serial instead of `None`, so the device bar only ever reverts to the bare serial for a serial
it has truly never resolved before, not merely one that's momentarily unplugged.
`ia_agent/api/device.py`'s `_device_model()` is now a thin wrapper calling `resolve_model`;
a new `_effective_serial()` (`pinned_serial() or ANDROID_SERIAL`) replaces every direct
`ANDROID_SERIAL` read in the router — `GET /api/device`'s `serial`/`model` and both
`POST /api/device/scrcpy/{start,stop}` calls now target the pin when one is set, while
`services/selftest.py`'s own adb functional test is deliberately untouched, since that's
about the pipeline's actual driven device (`Insta-Automate/.env`'s own `ANDROID_SERIAL`), a
different question from which device the control center's own bar/mirror show. Two new
routes for finding #2: `GET /api/device/adb-devices` (every serial `adb` currently knows
about, online or offline, via `adbutils.AdbClient.list()` — deliberately not the
`device_list()`/`iter_device()` filtered-to-online view, so a user can still pin a serial
that's briefly disconnected) and `PATCH /api/device/pinned-serial` (`{serial: string|null}`,
`null` clears the pin). `GET /api/device`'s payload grew `pinned_serial`/`default_serial` so
the client can always show "pinned to X, default is Y" rather than losing track of what the
override actually overrides.

**What shipped, app side (`app/`).** `core/device_models.dart`'s `DeviceStatus` gained the
two new optional fields (kept optional, not required, so the six existing test call sites
across `live_layout_test.dart`/`overview_layout_test.dart`/`shell_layout_test.dart` didn't
need touching) plus a new `AdbDeviceInfo`. `features/live/device_bar.dart`'s
`DeviceController` gained `fetchAdbDevices()`/`setPinnedSerial()` and a sibling
`adbDevicesProvider` (a plain unwatched `FutureProvider`, not folded into the polled device
status — the two have unrelated refresh cadences, and a failed adb lookup shouldn't blank an
otherwise-healthy device status). New `_DeviceIdentityCard` in
`features/settings/devices_tab.dart`, placed in its own "ADB device" section below the
existing pairing card per PLAN_V2.md's own note that these are two different systems (LAN
pairing vs. the ADB-connected phone) — a live adb-devices chip row to tap-to-pin, a manual
text field + Pin button for a serial that isn't currently attached, and a "Use default" button
that only appears once something is actually pinned.

**Verified.** `agent/tests/test_device.py` grew from 10 to 16 numbered checks plus a direct,
un-monkeypatched exercise of `device_settings.resolve_model` proving the cache-survives-a-
failure behavior with real code, not a stub (a `flaky_live` fixture that succeeds once then
raises, confirmed the second call still returns the cached model and that `live_lookup` was
genuinely called both times) — real `adbutils` itself stays monkeypatched at
`device_api._device_model`/`_list_adb_devices` for the endpoint-level checks, the same
`wsl_bridge`-fake pattern this file already used, since this environment has no real adb
server to hit. All 15 other agent suites re-run clean (one `test_supervisor.py` failure
turned out to be a stale lock file left by an earlier interrupted run in this same session,
confirmed by deleting it and re-running clean — not a regression). `flutter analyze` clean,
`flutter test` 226 total / 225 passing (225 prior + 1 new in `devices_layout_test.dart`
covering the pin/clear round trip and confirming no overflow at the 1024px floor; the one
failure is D114's same pre-existing, unrelated `shell_layout_test.dart` issue, reconfirmed via
`git stash` on the branch tip before writing any code here). `flutter build windows --debug`
succeeds. Verified live against the real agent: restarted to pick up the new code (`adb`
showed its own pre-existing restart churn from the phone still being disconnected per D116,
unrelated; the other two supervised services stayed `adopted` with uptime intact), a real
`GET /api/device`/`GET /api/device/adb-devices`/pin/clear round trip over `curl`, and the real
`device.json` confirmed empty again afterward (the throwaway test pin was cleared, not left
behind). Built and started for you per rule 5. **Not yet checkpoint-tested live** — the phone
being disconnected (D116) means model caching itself can't be exercised against a real device
this session; the pin/dropdown mechanics can still be checked once you're at the app.

---

## 2026-08-10 — Nine live bugs/feature requests grouped into three checkpoints ahead of release (D121)

### D121 · V2.13.1/V2.13.2/V2.13.3 inserted between V2.12 and the renamed V2.14; planning only, no code changed

**Ask.** With V2.5–V2.12 all accepted, the user brought nine things found using the real app
— too many for one checkpoint, not release polish, and explicitly not meant to block V2.13
(motion/accessibility/release) from eventually running last. Asked for them to be grouped
into exactly three sub-checkpoints named `V2.13.X`, with the existing V2.13 renumbered to
make room — implementation deferred to a future session.

**Grouping.** By touched surface, not by raising order:

| New checkpoint | Items (as given) | Surface |
|---|---|---|
| **V2.13.1** — Device identity | #1 (cache model over serial), #2 (manual serial + adb dropdown in Settings) | `core/device_models.dart`, `DeviceBar`, agent's `GET /api/device` |
| **V2.13.2** — Library review mode refinements | #4 (Review nav lands on the wrong folder), #5 (Apply shouldn't require every image decided), #7 (review mode should keep the nav rail visible, not go full-screen) | `review_page.dart`, `nav_rail.dart`'s Review entry, D115's full-screen decision |
| **V2.13.3** — Dashboard & shell fixes | #3 (Overview caps tile stuck on yesterday after flows stopped and the day rolled over), #6 (nav rail collapse button needs a precise click), #8 (status labels too small), #9 ("This machine" → "Host") | `caps_tile.dart`, `nav_rail.dart`'s `_CollapseToggle`, `ui/status.dart`'s `StatusChip`, `dependency_models.dart` |

Items #4/#5/#7 group naturally — all inside Library review mode. #1/#2 group naturally —
both are the same device-identification surface, just different-sized asks. #3/#6/#8/#9 are
a deliberate leftover bucket: four small, unrelated, contained fixes, grouped together
because none is large enough to deserve its own checkpoint on its own.

**Renumbering.** The former V2.13 ("Motion, accessibility, release") becomes **V2.14** —
content unchanged, still the last checkpoint in the plan, still gated on everything before it
being done. `pubspec.yaml`'s `2.0.0+1` bump and the `v2.0.0` tag move with it.

**Scope exception, flagged rather than silently absorbed.** V2.13.1 is the first checkpoint
in the whole v2 plan expected to touch `agent/` — model caching and an adb-device-list
endpoint are both agent-side. PLAN_V2.md's scope boundary ("v2 is entirely within `app/`")
is otherwise still in force; this is one deliberate, acknowledged exception, the same class
of call as the 2026-08-05 cross-repo deviation (D113), not a precedent for future checkpoints
to quietly do the same.

**Investigation flagged, not resolved.** #3 (stale caps tile) has two live hypotheses in
PLAN_V2.md's V2.13.3 section — a lazily-created day-counter row on the agent/pipeline side
that never rolls over while every flow stays stopped, or a client-side fallback in
`caps_tile.dart` that doesn't re-derive "today" from the wall clock — neither confirmed this
session. #5 (partial Apply) has a concrete reusable primitive already identified (D90's
`POST /api/library/move` + the existing explicit-path `delete()`, sidestepping `apply()`'s
whole-directory assumption entirely) but no full design (what "Apply" says when images are
left gray, whether a folder can be resumed later) — both left for the implementation session.

**Full checkpoint content** — goals, findings, and checkpoint tests for all three — lives in
[docs/v2/PLAN_V2.md](docs/v2/PLAN_V2.md)'s own V2.13.1/V2.13.2/V2.13.3 sections, not
duplicated here.

---

## 2026-08-10 — V2.12 (Command palette) built, planned and completed in one session at your request (D119)

### D119 · `Ctrl+K` wired to a real registry sourced from eight existing providers; three action paths deduplicated to feed it without a second implementation; Settings/Insights gain tab-jump, Limits gains a "jump to field" highlight

**Scope.** [SCREENS.md](docs/v2/SCREENS.md) §8's own source table, built exactly as specified:
`ui/command/` (registry, fuzzy matcher, palette UI, recents), every group wired to the provider
that screen already reads, every action reusing an existing controller call/confirm dialog rather
than a second implementation. `core/shortcuts_reference.dart` regenerated from a registry, per the
plan's own line — see the honest scope note on that below.

**New `app/lib/ui/command/`:**
- `command_item.dart` — `CommandItem` (id/group/label/subtitle/badge/icon/keywords/onSelect) and
  the fixed `commandGroupOrder` from SCREENS §8 (`Go to, Flows, Library, Services, Ops, Appearance,
  Settings, Help`).
- `command_matcher.dart` — case-insensitive fuzzy **subsequence** matching (every query character
  must appear in order, not necessarily contiguous — "scr" matches "Trigger now: Scrape" per the
  mockup's own example), scored so a prefix match always outranks a later subsequence match, groups
  always sorted by `commandGroupOrder` regardless of match strength, and every tie broken by an
  explicit original-index tiebreaker rather than trusting `List.sort` to be stable (it isn't
  guaranteed to be) — caught before it could become a real flaky-order bug, not found live.
- `command_registry.dart` — `buildCommandItems(context, ref)`, one function pulling all ~90+ live
  items from `flowsControllerProvider`, `libraryFoldersControllerProvider` +
  `libraryEntitiesControllerProvider`, `servicesControllerProvider`, `opsSpecsProvider`,
  `themeControllerProvider`, `configControllerProvider`'s int-typed schema, plus the seven nav
  destinations, six Settings tabs, three Insights tabs and two Help actions. Every `onSelect`
  closure calls an existing function — `forceRunFlow`/`stopFlowRun`/`reduceReserveFlow`/
  `toggleFlowSwitch`, `openReviewModeForFolder`, the new `service_actions.dart`/`ops_actions.dart`
  (below), `showShortcutsReference`/`showWelcomeDialog` — never a parallel copy of what any of
  those already do, including their confirm dialogs.
- `command_recents.dart` — `RecentCommandsNotifier`, persisted via `shared_preferences` (same
  synchronous-default-then-load shape as `LibraryZoomNotifier`/`ThemeController`), floats up to 8
  recently-used commands to the top as a "Recent" pseudo-group when the query is empty, deduplicated
  against the normal grouped list below it rather than shown twice.
- `command_palette.dart` — `showCommandPalette(anchorContext)` + `CommandPalette`. Built as a
  `showDialog` with a custom `Align`+`AppOverlay` body (not `AppDialog`, which is a fixed-width
  centered `AlertDialog` — wrong shape for a top-anchored, tall, keyboard-driven list), `CallbackShortcuts`
  for ArrowUp/ArrowDown/Escape/Enter over a plain `TextField` (matching this app's own
  `search_field.dart` precedent for the same "shortcuts win, typed characters still reach the field"
  shape), and — the one non-obvious wrinkle — every action closure is built against the **caller's**
  stable context (`anchorContext`, the title bar's or `AppShell`'s own, passed down at
  `showCommandPalette` call time), never the dialog route's own `context`, because activating a
  command almost always changes what's on screen (a nav-index write) out from under the dialog
  that's popping at the same moment.

**Deduplication, not new confirms — three action paths shared with the palette, not copied for
it (all pre-existing, all left behaving identically to before):**
- `core/service_actions.dart` — `startService`/`stopService`/`restartService`/`takeoverService`/
  `testService`, lifted out of `ServiceDetail`'s private `_start`/`_stop`/`_restart`/`_takeover`/
  `_test` (same confirm dialogs, same `serviceStopConsequence` map, same error-snackbar shape).
  `ServiceDetail` itself now calls these too — its own busy-spinner state is the only thing that
  stayed local, since the palette has no per-button spinner to drive.
- `core/ops_actions.dart` — `runOpsJob`, lifted out of `OpsTab._run` (confirm-if-`spec.confirm`,
  start, fold a 409 into "a job is already running" same as before). `OpsTab._run` now just calls
  it and keeps its own "select the freshly-started job in local history" behaviour.
- `core/flow_switch_confirm.dart` gained `toggleFlowSwitch` (confirm-if-turning-off, apply, catch
  `DioException` into a snackbar) — `flow_node.dart`'s private `_toggleSwitch` deleted in favour of
  it, one call site instead of two.

**Settings/Insights gain a tab-jump they had no way to receive from outside before.**
`DefaultTabController` only ever builds its underlying `TabController` once per mount — a rebuild
with a different `initialIndex` alone does nothing. New `core/settings_nav.dart`'s
`requestedSettingsTabProvider`/`requestedInsightsTabProvider` (plain `Notifier<int>`) are read into
`initialIndex` **and** used as the `DefaultTabController`'s own `Key`, forcing a real remount onto
the requested tab when the palette (or anything else) writes a new value. `InsightsPage` moved from
`StatelessWidget` to `ConsumerWidget` to read it; `SettingsPage` (already a `ConsumerWidget`) just
gained the watch.

**"Jump to its field" for a `Settings` config-key result is a real scroll-to-and-flash, not just a
tab switch.** `limits_tab.dart` moved from `StatelessWidget` to `ConsumerStatefulWidget` to hold a
`GlobalKey` per `LimitCard` (built lazily, cached across rebuilds) and call
`Scrollable.ensureVisible` when `highlightedConfigKeyProvider` (new, `settings_nav.dart`, a
generation-counted auto-clearing `Notifier<String?>` — the counter exists so an older highlight's
delayed clear can never stomp a newer one fired before it expires) names a key. `LimitCard` gained a
`highlighted` bool wired straight to `AppCard(selected: ...)` — the existing selected-state tint and
accent ring, not a new visual language, snapping on then auto-clearing after ~2.2s.

**`Ctrl+K` and the shortcuts reference — a single source, honestly scoped.** New
`core/global_shortcuts.dart`'s `globalShortcuts` list (id + `SingleActivator` + display keys +
description) is now what both `shell/app_shell.dart`'s `CallbackShortcuts` bindings map **and**
`core/shortcuts_reference.dart`'s Global-scope rows are built from — a shortcut added to the list
without a matching action in `app_shell.dart`'s `actionsById` map now fails loudly (a missing map
key) instead of the two lists silently drifting apart the way this file's own pre-V2.12 comment had
to warn future editors about by hand. `Ctrl+1..7` became seven individually-described rows ("Jump to
Overview" … "Jump to Settings") rather than one collapsed "Ctrl+1..7" summary line, since the
per-destination id was already needed for the action map — a genuine small improvement, not scope
creep. **Deliberately not folded into the same mechanism, and said so in the file's own comment
rather than forced into a shape that doesn't fit:** `Ctrl+Alt+I` is a real OS-level `hotkey_manager`
registration (`shell/hotkey.dart`), not a Flutter `CallbackShortcuts` binding, and every
Settings/Library key handler (`Ctrl+E`, `Ctrl+F`/`Esc`, the whole Library selection key map) is a
page-scoped handler with no shared registry of its own to generate from — both stay hand-listed,
same as before.

**Verified:** `flutter analyze` clean. `flutter test` 224 total, 223 passing — the one
`shell_layout_test.dart` "rail expanded" failure reconfirmed pre-existing and unrelated via
`git stash` on the branch tip (same D114/D118 precedent), not touched by this session's changes.
New `test/command_palette_test.dart` (10 checks): the matcher (subsequence survives non-contiguous
letters, a fully-absent letter matches nothing, a prefix beats a later subsequence match in the same
group, group order is fixed regardless of input/match order, an empty query preserves registry order
via the explicit tiebreaker, `groupCommands` buckets and drops empty groups); the registry (every
group populated from its real provider and gated exactly like its source screen — `entity-follow`-
only "Reduce reserve" absent when only `entity-scrape` is faked, `Start`/`Test` absent for an
already-running, no-test-capable fake service, real badges for folder counts and a config value);
and the palette widget itself (typing narrows to one match and tapping it both closes the dialog and
performs the exact same provider writes `curation_tile.dart`'s own "open in Library" helper makes,
recording it into recents; `ArrowDown`/`ArrowDown`/`Enter` activates the third `Go to` item with no
mouse touch at all; `Esc` dismisses without invoking anything). `flutter build windows --debug`
succeeds. Three stale running instances killed, one fresh instance built and started for you per
rule 5 — **your checkpoint test is what's still open**: `Ctrl+K` from every screen, search for a
flow/folder/ops job/theme/config key, confirm a destructive action invoked from the palette still
prompts, confirm `Esc` dismisses and focus returns where it was.

### D120 · Same-session fix: ArrowDown/ArrowUp moved the highlight past the visible rows with nothing on screen following it

**Found by your own checkpoint test, immediately.** Mouse-wheel scrolling worked; arrow-key
navigation didn't visibly do anything once the highlighted row scrolled past the palette's fixed
480px body — the highlight index was updating correctly (confirmed by the two keyboard-nav tests
already passing), the list just never scrolled to keep it on screen.

**Fixed** with the same `GlobalKey` + `Scrollable.ensureVisible` technique `limits_tab.dart`
already uses for the palette's own "jump to a config field" highlight (D119): one `GlobalKey` per
row, rebuilt fresh each frame and only ever read back from that same frame's own
`addPostFrameCallback` — safe because arrow-key navigation only ever moves the highlight by one row
at a time, so the newly-highlighted row is always adjacent to whatever was already visible, never a
jump `ensureVisible` could fail to resolve against an unmounted target. The result list itself moved
from `ListView` to a `SingleChildScrollView` + `Column` in the same change — a plain `ListView`
virtualizes, meaning a row several screens away from the visible viewport has no mounted `Element`
at all yet, so its `GlobalKey.currentContext` would still be `null` the first time `ensureVisible`
needed it after a large jump (typing a query that changes which item holds focus, for instance).
The registry here tops out around 150 items even fully realized, so the always-mounted tradeoff
costs nothing meaningful.

**Verified:** a new regression test in `command_palette_test.dart` (12 total in that file now) —
confirmed to actually fail against the pre-fix code (temporarily disabled the `ensureVisible` call,
re-ran just this test, watched it fail with the scroll offset stuck at 0 after 20 `ArrowDown`
presses, then restored the fix and reconfirmed green) before trusting it as a real regression
guard, not just a passing assertion. `flutter analyze` clean, `flutter test` 225 total / 224
passing (same pre-existing, unrelated `shell_layout_test.dart` failure). `flutter build windows
--debug` succeeds. Rebuilt and restarted for you. **You confirmed live afterward, including the
arrow-key scroll fix — V2.12 accepted.**

---

## 2026-08-10 — V2.11 (Services, Insights, Settings) built out of D107's planned sequence order, at your explicit request (D118)

### D118 · V2.11 built before V2.12; several of PLAN_V2.md's own premises were already stale; `AppTable` gets its first real call sites; one real overflow bug found by the extended test suite

**Order swap, not a re-plan.** D107 sequenced the "functional" group as V2.10 → V2.12 → V2.11,
V2.11 last since its own additions (terminal search/copy/font-size, resizable panes) were judged
least load-bearing. You asked to do V2.11 first instead. PLAN_V2.md's own sequencing notes already
say nothing in V2.5–V2.12 depends on anything else in that range, so the swap is safe — V2.12
(Command palette) is simply next once this checkpoint is confirmed.

**Surveyed before writing any code** (three parallel Explore passes over Services/Insights/
Settings plus the current `app/lib/ui/` component library) and found several of PLAN_V2.md's
premises already fixed by earlier checkpoints or already built with the exact shape needed —
skipped rather than redone: `service_detail.dart`'s claimed hardcoded hex colors (none found, already
tokened via `tokens.status.*`), `service_terminal.dart`'s claimed hardcoded `'Consolas'`/inline
`TerminalTheme` (already fully `tokens.terminal`-driven since an earlier checkpoint), and
`devices_tab.dart`'s claimed `Colors.white` QR quiet-zone (already `tokens.chart.qrQuietZone`,
defined per-theme). Also found: `AppTable` (COMPONENTS §10) has existed since it was built but had
**zero real call sites anywhere in the app** — this checkpoint gives it three (Ranking, Dependencies,
Ops job history), the first real proof the D77 flexible-column invariant holds outside its own
synthetic test.

**One shared-component change**: `AppTable` gained an optional `isSelected: bool Function(T)?`
(tints a row like a selected list tile) — Ops' job history needs it to show which job's log is open
next to it, the same way `AppPanel` gained `accentEdge` and `AppButton` gained `busy` from their own
first real callers. `IconAction.icon` was widened from a raw Flutter `IconData` to the same
`PhosphorIconData Function(PhosphorIconsStyle)` shape `AppIcon` already uses — its first real call
site (the Services terminal's new Clear/font-size/Find/Copy controls) revealed the original type
couldn't actually take any of this app's own `AppIcons.*` glyphs at all.

**Services**: `ResizableSplit` replaces the fixed 300px list↔detail split and, new, a fixed
"panels minus terminal floor" calculation inside `ServiceDetail` (now a real vertical
`ResizableSplit`, `services.detail.split`). `ServiceTile` gained `accentEdge` off the existing
`ServiceStateStatusKindX` bridge; the self-heal icon's plain `Tooltip` became a rich `AppTooltip`
with a title/body split. The terminal frame gained two genuinely new pieces with no existing
pattern to adapt (`LogConsole` has neither either): a **Clear** button (`Terminal.eraseDisplay()`,
confirmed present on `xterm: ^4.0.0`, a local-only visual clear — the next replay/reconnect still
repopulates from the agent's ring) and a persisted **font-size** control (`TerminalFontSizeNotifier`,
same synchronous-default-then-load shape as `LibraryZoomNotifier`, four steps 11–17px). Every
header/search-bar icon button migrated to `IconAction`.

**Dependencies — a judgment call, not literally what SCREENS §4 pictured.** Its "ten dependencies
as sortable rows (name · state · detail · latency)" reads naturally as one flat, sortable
`AppTable` across all ten rather than the four group-partitioned sections the old bespoke rows had
— sorting by State (worst-first default) surfaces every failure together regardless of group,
matching the file's own standing comment ("the value is knowing which one is why a flow is
failing"). Each group's explanatory blurb moved from an always-on text block into a rich
`AppTooltip` on the row's Group cell.

**Insights**: `AppPage.maxContentWidth: 900` replaces `FunnelTab`'s own local `ConstrainedBox`,
now applied to all three tabs per the plan text, not just Funnel. `RankingTab`'s D77 hand-built
table is now a real `AppTable<EntityRanking>` — same columns, same row-tap-opens-the-entity-
dialog, sort state moved to `AppTableSort`. `FunnelChart` retokened to `tokens.chart.*` (was
`ColorScheme.primary`/`.surface`) and gained a real stage-by-stage draw-in animation — a new
`StatefulWidget` driving a `reveal: List<double>` into `_FunnelPainter` via per-stage `Interval`
sub-animations (each stage's own interval doesn't begin until the previous one's has finished, so
by the time a later stage starts revealing the earlier one is already at its real, static width),
collapsing to instant under `tokens.motion.reduced`. `BurndownTab` gained the "today vs cap"
summary strip by reusing Overview's `CapsTile` directly (already exactly the right shape, no new
widget needed) above the day-range chips. Cross-links: `Scanned`/`Female`/`Scraped` funnel stages
jump to their matching Library folder (`scanned/`, `gender_valid/`, `scraped/`) via the same
`_openLibrary` pattern `CurationTile` already uses; `Private` and `Followed` stay plain labels —
neither has a real matching folder (same reasoning D81 used to drop both from the per-entity yield
dialog), so neither gets a link that would land somewhere misleading.

**Settings**: `LimitsTab`'s ad hoc group `Text` headers became `SectionHeader(title, caption)`.
`DevicesTab` gained two `SectionHeader`s for visual consistency — otherwise already close to spec
(QR quiet-zone and `AppPanel` structure both already done, per the stale-premise findings above).
`switches_tab.dart`'s migration to `AppSwitch(confirmMessage: ...)` was evaluated and **not done**:
`AppSwitch`'s confirm dialog has a fixed generic title ("Turn this off?"), while
`confirmFlowSwitch`'s current dialog title names the exact flow ("Turn off ENTITY_SCAN?") and the
per-flow consequence body text never repeats the flow name itself — migrating would have silently
dropped which flow the dialog is even about. Left as its existing hand-rolled, flow-specific
version rather than force an optional simplification through a real information loss.
`queue_tab.dart` was already compliant (its one numeric field already renders through
`NumericText`; the count chips are composed label strings via `StatusChip`, matching every other
composed-count chip in the app, not a bare numeric display).

**Ops job history → `AppTable`, one real overflow bug found by the extended test suite, not by
writing the code.** The first version used the plan's literal four columns (Status/Job/Started/
Elapsed); `ops_layout_test.dart`'s existing 1024×700 overflow test caught a real `RenderFlex`
overflow immediately — the History sidebar is a fixed 280px, ~250px once the table's own row
padding is subtracted, and three fixed-width columns (90+110+90) alone already exceeded that
before the flexible Job column got anything. Fixed by combining Started/Elapsed into one narrow
`_WhenCell` (two stacked lines: relative time, then elapsed) instead of dropping either piece of
information. The elapsed timer itself reuses `run_summary.dart`'s exact `StreamProvider.autoDispose`
tick pattern (watched only while `status == running`, so finished rows never rebuild on the clock)
and `flow_status.dart`'s existing `formatFlowCountdown`, not a new formatter. The five destructive-
job confirm dialogs, the button grid's D72 overflow fix, and the log panel are all untouched, per
the plan's explicit instruction.

**Verified:** `flutter analyze` clean throughout every round. `flutter test`: 214 total, 213
passing — the one failure (`shell_layout_test.dart`'s "rail expanded" case, an icon-size assertion
unrelated to anything touched here) reproduced identically via `git stash` on the branch tip
*before* any of this session's changes, confirming it's the same pre-existing, standing issue
D114/D116 already documented, not a regression. New/extended coverage: `ui/data_test.dart` (the
`isSelected` tint), `services_layout_test.dart` (the new terminal controls, the Dependencies table
with a long detail sentence), `insights_layout_test.dart` (funnel stage tap → `selectedFolderProvider`/
`selectedNavIndexProvider`, `CapsTile` present in `BurndownTab`), `ops_layout_test.dart` (the
overflow catch above, plus a deterministic finished-job elapsed-value check), `devices_layout_test.dart`
(the new `SectionHeader`s render without overflow). `flutter build windows --debug` succeeds. Built
and started for you per rule 5 — **your checkpoint test is what's still open**: terminal search/
copy/clear/font-size against a real streaming service; Ranking sorts and rows still open the
entity dialog; run one non-destructive ops job (Deploy flows / Reset work pool) and watch the live
log + elapsed timer; confirm the five destructive jobs still prompt; funnel stage taps land on the
right Library folder; Dependencies sorts by state with failures surfaced together.

**You confirmed the full checkpoint test live 2026-08-10 — V2.11 accepted.**

## 2026-08-09 — adb self-heal crash-looped forever once the phone was disconnected, colliding with a stray external `adb start-server` it could never recognize (D117)

### D117 · Two chained self-heal bugs, both only reachable with no phone attached: blind respawn colliding with a stray external adb daemon, and a 60s restart-forever loop against a perfectly healthy server

**Reported live**, with the exact log lines: `adb` was crash-looping every ~60s —
`could not install *smartsocket* listener: cannot bind to 0.0.0.0:5037: Only one usage of each
socket address... (10048)`, `process exited with code 3221226505`, `self-heal: restarting in 60s`,
forever, starting right after you disconnected the Android phone (your own deliberate call, to
pause the pipeline for a few days — see D116's same context). Your own framing, once the shape of
the bug was clear: on this machine port 5037 is always meant to belong to this service — if
anything else is ever found holding it, just kill it and let the app run its own copy. That
directive is exactly what both fixes below implement.

**Bug 1, diagnosed live, not guessed**: `GET /api/services` showed `adb` in `state: "backoff"`,
`origin: "none"`, `port_owner: null` — yet its own `probe.detail` said `"tcp 127.0.0.1:5037 open;
device ... not attached (saw none)"`, i.e. the raw TCP port genuinely was listening the whole
time. `Get-NetTCPConnection`/`Get-CimInstance Win32_Process` confirmed the real owner: PID 4244,
command line `adb -L tcp:5037 fork-server server --reply-fd 868` — not our supervised
`-a nodaemon server start` invocation at all. That command line is ADB's own built-in
"no server found, auto-start one" client behavior — some other tool that shells out to plain
`adb` (VS Code's Dart/Flutter extension, `flutter devices`, or any manual `adb` command — this
machine runs Flutter dev tooling in the same session) auto-spawned its own detached background
daemon into a gap where our supervised server happened to be down, and that daemon then persisted
indefinitely, permanently squatting on the port.

**Root cause: `ManagedService._probe_idle()`'s self-heal branch, and `Supervisor.start()`'s own
boot-time bootstrap, both gated "is someone else already on this port?" behind the *compound*
probe result** (`ProbeResult.ok`, TCP-open AND `probe_extra`), not the raw port-open signal alone.
`adb`'s `probe_extra` (`adb_device_present`) can never pass while no phone is attached, so
`self.probe.ok` can never be True, so `detect_external()` (the one thing that would have
recognized "a real, functioning adb server already owns this port, don't spawn a second one") was
never reached at either call site. Self-heal just blindly re-spawned on top of the live foreign
daemon every retry, and every spawn crashed on the identical bind conflict, forever.

**Fixed at both call sites** by checking raw port ownership (`_port_owner()`, the same lookup
`detect_external()` already uses internally) independently of the compound probe — `_probe_idle()`
checks it before calling `_spawn()` and calls `detect_external()` + `takeover()` instead of
colliding if someone else holds it; `Supervisor.start()` calls `detect_external()`
unconditionally for an unadopted service (not gated behind `probe.ok` first) and, when the result
is `EXTERNAL` with the service's own `autostart`+`self_heal` both on, takes it over immediately
rather than leaving it for a human to notice and click "Takeover" — the same "self-heal means truly
unattended recovery" standard this codebase already set at D74/D82/D91.

**Bug 2, found while verifying the live fix for Bug 1, not reported by you**: `restart_count`
climbed from 0 to 51 over about 27 minutes on the live machine — `adb` was alive, correctly
supervised, its port genuinely open the whole time, yet self-heal kept killing and respawning it
anyway. Root cause: `_probe_alive()`'s "wedged" self-heal (`unhealthy_grace`, 60s by default) fires
whenever the *compound* probe fails continuously, which is exactly `adb`'s permanent state with no
phone attached — the mechanism built to catch a process that holds its port but answers nothing
was instead firing on a process answering exactly what it should (no device), forever, for as long
as the phone stays disconnected. Each of those restarts also reopened Bug 1's exact collision
window, so this wasn't just noise — it was actively re-triggering the original failure mode on a
schedule.

**Fixed by adding `ProbeResult.transport_ok`** (`probes.py`) — the transport-level check (TCP
connect / HTTP GET) alone, captured before `probe_extra` is ever consulted — and keying the wedge-
restart timer off *that* instead of the compound `ok`, resetting it the instant the transport
recovers (mirroring `_healthy_since`'s existing pattern) so a real, sustained transport failure
still restarts on schedule exactly as before, but a semantic-only failure like "no device" never
does.

**That fix's own first version had a real flaw, caught by its own regression test flaking, not by
you**: it reused the *existing* `_unhealthy_since` timestamp (set once, back when the compound
probe first failed) as the elapsed-time base for the new `transport_ok` check, rather than tracking
"how long has the transport itself been continuously failing" as its own independent clock. That
meant a single transient transport hiccup — one slow probe under load, not a real failure — could
immediately satisfy an already-elapsed grace window and restart, instead of requiring the
transport to actually be down for the full `unhealthy_grace`. Fixed by tying `_unhealthy_since`'s
reset directly to `transport_ok` (reset to `None` the instant it's True, same tick discipline as
`_healthy_since`), so it now measures continuous transport failure specifically, never a stale
timestamp left over from an unrelated compound-probe failure.

**Chasing that flake down also surfaced a test-design bug, not a supervisor bug**: the regression
test's own `start_grace=0.5`/`unhealthy_grace=1.0` were tuned far tighter than a real subprocess
spawn can guarantee — instrumenting the exact tick sequence showed the blocking spawn handshake
alone (subprocess creation, ConPTY setup, interpreter start) taking over 2 seconds by itself under
a loaded test run (16 prior sections' worth of process churn happening moments before), well past
either constant. The fix logic was correct throughout; the test was racing real, if slow, spawn
latency against unrealistically tight timers. Rewritten to wait for the transport to genuinely come
up first (decoupled from spawn-latency variance entirely) before starting the "assert no restart"
window, rather than trying to out-guess real-world timing with bigger constants.

**Verified, in order:** four new regression checks in `agent/tests/test_supervisor.py` — #15
reproduces Bug 1 exactly (spawns a real conflicting process during a service's `BACKOFF` wait,
confirms self-heal reclaims it instead of crash-looping); #16 the same at `Supervisor.start()`'s
boot path; #17 reproduces Bug 2 (a `probe_extra` that never passes, confirms zero restarts over a
window comfortably past `unhealthy_grace`, redesigned as above once its first version flaked under
load for the reason described). Full suite, final and clean: **80/80** (was 57 before this session
— corrected in `agent/tests/README.md`). `ruff check` clean throughout every round.

**Verified against the real live machine, twice** — once after Bug 1's fix alone (confirmed it
reclaimed PID 4244 cleanly, `origin: "supervised"`, narrated `"reclaiming port 5037 from an
external process found already listening at startup"` in its own log), and again after Bug 2's fix
once the live `restart_count: 51`/uptime reset every ~30s made that second bug undeniable on the
running system too. Restarted `ia-agent.exe` (`taskkill /F`, the launcher respawned it in ~3s per
the established D21 pattern) with both fixes applied; the adb service adopted its already-running,
already-reclaimed process (`origin: "adopted"`, same pid, uptime carried over — the correct D22
behavior, no needless respawn) and settled into `state: "unhealthy"` (port open, no device attached
— the correct, expected state with the phone unplugged, not a crash loop) with `restart_count: 0`
and no further cycling observed over the following watch window. No pipeline/cross-repo change
needed; this was entirely inside the agent.

---

## 2026-08-09 — Overview's "Today's caps" tile could contradict a live notification on the same screen (D116)

### D116 · `CapsTile`'s "today" figure now reads from the live scheduler heartbeat, not the once-per-session burndown fetch

**Not v2 work, a live-found bug fix — a deliberate one-session deviation from the v2 sequence, same standing precedent as D113.** V2.12 (Command palette) is still next whenever this branch resumes the checklist.

**Reported live, with a screenshot**: the Overview page's "Today's caps" tile showed Scrape at
200/300 for 2026-08-08, while the "Recent" tile on the same page — fed live over the
`notifications` WS channel — showed "Scrape limit reached for 2026-08-08. Limit: 300", delivered
minutes earlier. Investigated by querying the real Prefect API (27 non-overlapping `entity-scrape`
runs that day, ruling out a concurrent-run write race) and the agent's own `/api/insights/burndown`
directly, which returned the correct, current value: `{"date": "2026-08-08", "scraped": 300,
"processed": 414}`. **The notification was correct; the tile was stale — not a pipeline/DB bug at
all.**

**Root cause: `burndownProvider` (`insights_controller.dart`) is a plain, non-`autoDispose`
`FutureProvider` — fetched once, cached for the rest of the app's process lifetime, and never
invalidated automatically anywhere.** Its own doc comment says "fetched once per screen visit,
refreshed by invalidating this provider... nothing about the underlying Postgres data changes fast
enough to justify a WS channel or a timer" — a reasonable call for the Insights page, which the
user visits briefly and can hit an explicit retry button on. It was wrong for the Overview tile,
which sits open on screen for hours at a time and, unlike Insights, has no retry affordance at
all — so its "today" number just freezes at whatever it was on first load and silently drifts
further from reality as the day's flows keep running, eventually landing right next to a live
notification that visibly contradicts it.

**Fixed by sourcing "today" from data that's already live, not by adding a new poll/timer.** The
scheduler heartbeat (`controllers/prefect.py`'s `_today()`, posted to the agent every ~2s and
already mirrored into the app via the existing `flows.state` WS channel and
`flowsControllerProvider` — the same live source `FlowCard`'s own counters use) already carries
exactly this number (`{"scraped": scrape.scraped, "limit": ...}` etc.) for every flow with a daily
cap. `CapsTile` now takes an optional `liveFlows` map and prefers
`liveFlows[flow]?.today[field]` for the headline bar/count, falling back to the burndown history's
last day only while the live snapshot hasn't loaded yet. The 7-day sparkline trend is untouched —
still from `burndownProvider`, since past days are immutable once the calendar day rolls over, and
only "today" was ever the volatile, wrong number.

**Rejected:** polling `burndownProvider` on a timer, or invalidating it on notification arrival —
both would still be a second, redundant round trip for data the app already has live via the
heartbeat it already subscribes to for the Pipeline tile one row above.

**Verified:** `flutter analyze` clean; `flutter test` 210/211 (the one `shell_layout_test.dart`
failure reconfirmed pre-existing via `git stash` — identical failure on the unmodified branch tip,
unrelated to this change); `overview_layout_test.dart`'s 11 cases all still pass unchanged, since
they already exercise `CapsTile` through `_CapsTile` with `flowsControllerProvider` unoverridden
(falls back to burndown, matching the old behavior exactly when no live snapshot exists). Verified
against the real running agent's `/api/insights/burndown` and Prefect's real flow-run history
directly, read-only — no ops action taken, no code touched outside `app/`. Built and started for
you per rule 5 — not clicked through by Claude.

**The Android phone is disconnected indefinitely (your own call, to pause flows for a few days)**,
so this can't be checkpoint-tested against a *live* run reaching a cap the way it would normally be
verified — nothing will scrape/follow/scan while it's off. What you *can* still confirm without the
phone: open Overview and confirm "Today's caps" now shows figures consistent with yesterday's
(2026-08-08) real totals (`Scrape 300/300`, `Follow 155/60` — over cap by design, `Scan · profiles
2/10`, from the burndown numbers pulled above) rather than a lower stale count. A true live-updating
check (numbers ticking up in real time as a flow runs) is what's left open until the phone is back.

---

## 2026-08-08 — V2.10, Library review mode (D115)

### D115 · A full-window keep/discard decision buffer for one `(folder, entity)` at a time, writing only through the existing `POST /api/library/apply`; the double-click lightbox lands in the same session

**Built per PLAN_V2.md's `## V2.10 — Library review mode` / SCREENS.md §5b-§5c** — the headline
feature of all of v2, next after V2.8 in the fixed V2.6→V2.7→V2.9→V2.5→V2.8→V2.10→... sequence
(D107). New `app/lib/features/library/review_page.dart`: `LibraryReviewPage` (the decision
buffer) and `LibraryLightboxPage` (§5c's browse-only sibling — prev/next, no buffer) share the
same large-image stage, pushed as a genuine full-screen route via
`Navigator.of(context, rootNavigator: true).push(...)` — this covers the title bar and nav rail
entirely, matching SCREENS.md's own mockup (no app chrome shown at all), a deliberate reading of
"full-window" over a variant that keeps the shell visible. Esc always returns to it.

**The keyboard map is exactly SCREENS §5b's table** — `→`/`L` keep-and-advance, `←`/`H`
discard-and-advance, `↑`/`K` back one *and un-decide it*, `Space` toggles the current decision
without advancing, `Enter` applies, `Del` deletes the current image immediately (bypassing the
buffer, but still through the same confirm dialog every other delete path in this app uses —
SCREENS' "immediately" read as "not deferred to Apply," not "skip the confirm," since nothing
else in this codebase deletes without one), `Z` toggles zoom-to-fit/actual-size
(`LibraryFullImage`, new in `core/library_image.dart`, backing `GET /api/library/image` — the
original file, not the grid's thumbnail), `O` opens the real Instagram URL.

**Apply reuses `applyLibrarySelection`, extracted from `library_toolbar.dart`'s private `_apply`
into a shared top-level function** (same shape as the existing `deleteLibrarySelection`) — the
toolbar's own Apply button and review mode's Apply both now call the identical
`POST /api/library/apply` + confirm dialog, so there is no second implementation of what "apply"
means or looks like.

**The one correctness rule PLAN_V2.md flagged as this checkpoint's real risk — "never present a
partial set as the whole folder," D90's mobile bug in a new shape — is enforced structurally, not
just documented.** `apply()` is whole-directory-scoped server-side (everything not selected gets
trashed), so Apply is disabled until every *loaded* image has a decision **and** `hasMore` is
false — reaching the loaded boundary while pages remain shows a spinner, not the "done" screen,
since `_maybePageMore` requests the next page well before the reviewer actually reaches it (a
20-item lookahead against the current position, not a scroll listener — there's no scrolling in a
one-at-a-time reviewer).

**A real bug this same rule surfaced, caught by the new test suite before it ever shipped, not
found live:** the first version called `loadMore()` directly from `_maybePageMore`, itself called
from `build()`. Riverpod forbids mutating a provider from inside a widget's own build — and the
real `LibraryImagesController.loadMore()` writes `state` (`loadingMore: true`) as its literal
first statement, so this would have thrown the identical assertion in production the moment a
reviewer paged past a folder's first batch, not just in the test harness. Fixed by deferring the
call through `WidgetsBinding.instance.addPostFrameCallback`.

**The double-click lightbox (§5c, ✅ already confirmed by the user in D98) landed in the same
session** — `library_tile.dart`'s double-click now opens `LibraryLightboxPage` instead of copying
the id; copy-id already lived in the right-click context menu too, so nothing is lost, matching
SCREENS' own framing. `library_grid.dart` passes the tapped tile's index as the lightbox's start
position.

**All four SCREENS-listed entry points exist**: the toolbar's own Review button (enabled exactly
like Apply/Delete — visible always, disabled with nothing loaded); `R` via a page-level
`CallbackShortcuts` in `library_page.dart`; and the nav rail's Review sub-item /
`pipeline_edge.dart`'s ⚑ tap, both upgraded from "navigate to the folder" (all they ever did) to
actually deliver on `pipeline_edge.dart`'s own long-standing comment — a new
`openReviewModeForFolder` selects the folder, awaits its first entity with a real backlog, and
pushes straight into review mode for it, rather than landing on "pick an entity to browse."

**Verified:** `flutter analyze` clean. New `test/review_mode_test.dart` (5/5) — Keep/Discard/
Back/Space's exact semantics including the Up-then-redecide case verified end to end against a
real (faked) Apply call; Apply staying disabled while more pages remain even with every *loaded*
image decided; the pagination-boundary `loadMore()` trigger (via a recording fake, not a real
agent); Esc popping the route and writing nothing; Del showing the shared confirm dialog and
writing nothing on Cancel. `FileOpener.openUrl` (the `O` key) is deliberately never exercised —
same reasoning `library_layout_test.dart` already established for the tile's own "Open on
Instagram" menu item, since it shells out to the real OS via win32 `ShellExecute`.
`flows_layout_test.dart`'s existing ⚑-edge test needed updating for the richer behavior (it now
also resolves an entity and pushes a real route) — without fakes for the folder/entity/images
providers it touches, the tap would have hit a real `dio.get` and left a pending `Timer` past
the widget tree's teardown; fixed with the same fake-controller shape `library_layout_test.dart`
already established. Full suite: 210 checks, 209 passing — the one `shell_layout_test.dart`
failure (`AppShell ... rail expanded`) reproduces identically on the pre-session branch tip
(confirmed via `git diff --stat` showing `nav_rail.dart`'s only change this session was a 10-line,
non-layout edit to `openReview()`), matching the same pre-existing failure D114 already recorded.
`flutter build windows --debug` succeeds. Two stale prior-session instances found running were
killed first and replaced with one fresh one (D87's precedent). Built and started for you per
rule 5 — not clicked through by Claude.

**Checkpoint test (yours, per PLAN_V2.md's own V2.10 gate — the only checkpoint that writes to
real curation data):** review a real batch end to end in `gender_valid` (or `scraped`), Apply it,
and confirm the files moved exactly as the grid's own Apply would have. Test `Esc` mid-batch and
confirm nothing was written. Test the pagination boundary on an entity with a large backlog — the
next page should already be loading well before you reach the end of what's on screen. Try the
four entry points (toolbar Review button, `R`, the nav rail's Review sub-item, a Flows ⚑ edge) and
the double-click lightbox. Then do the same review flow once more in `scraped`.

**Same-session follow-up, caught by your own retest: the small/medium/large zoom control reset to
medium on every restart.** `LibraryZoomNotifier` (`library_controller.dart`) never persisted at
all — `build()` always returned the hardcoded default. Fixed with the same pattern
`NavRailCollapsedNotifier` (`core/nav_state.dart`) and `ThemeController` already use: a
synchronous `LibraryZoom.medium` default so the first frame never waits on disk, `build()` kicking
off an async `SharedPreferences` read that updates `state` a moment later if a saved value exists,
and `set()` now persisting (`prefs.setString('library_zoom', zoom.name)`) alongside updating state.
`flutter analyze` clean, `flutter test` unchanged (16/16 across `library_layout_test.dart` +
`review_mode_test.dart` — the layout test's `_FixedZoom` fake fully overrides `build()` and never
touches `SharedPreferences`, so it was unaffected). Rebuilt and restarted for you.

**Same-session follow-up, your own request: `gender_invalid` moved from SCANNING into YOUR
REVIEW.** Purely a `libraryStageGroups` regrouping (`core/library_models.dart`) — `gender_invalid`
was classify's rejected-gender output with no curation step attached, unlike `gender_valid`/
`scraped`'s real pipeline gates (ARCHITECTURE §9's two human-in-the-loop steps); the user's own
call to give it a place to catch classifier mistakes rather than leave it unreviewable. No
behavior change beyond the grouping — review mode was already generically available for any
folder (the toolbar's Review button/`R` only ever gated on "is something loaded," never on which
folder), so `gender_invalid` could already be reviewed, it just read as pipeline state rather than
an invitation to. `curationFolders` (`overview/curation_tile.dart` — the Overview hero tile/
nav-rail badge/default review-entry-point folder) was deliberately left at just
`['gender_valid', 'scraped']`, since widening it would also grow the Overview's "needs attention"
surface area and nothing asked for that. Doc comments in `library_models.dart`/`library_rail.dart`
and the matching `library_layout_test.dart` assertion updated from "two" to "three" review
folders. `flutter analyze` clean, `flutter test` 11/11 in `library_layout_test.dart`. Rebuilt and
restarted for you.

**Same-session follow-up, your own request: YOUR REVIEW reordered to `gender_invalid` →
`gender_valid` → `scraped`.** A one-line reorder of the same `libraryStageGroups` list (was
`gender_valid` first). Rebuilt and restarted for you.

**Checkpoint test passed 2026-08-08 — you confirmed all four follow-ups plus the core review
flow live. V2.10 accepted.** Next: V2.12 (Command palette).

---

## 2026-08-08 — V2.8, Live screen rework (D114)

### D114 · Fixed 420px visualization column replaced with a resizable, expandable split; RunSummary dissolved into a header strip; log search and the scrape morph added

**Chosen, per PLAN_V2.md's `## V2.8 — Live` / SCREENS.md §3 scope** (V2.8 is next in the fixed
V2.6→V2.7→V2.9→V2.5→V2.8→... sequence, D107): the log console and visualization surface move
into a `ResizableSplit` (`persistKey: 'live.split'`, `initialFirstSize: 480` for the log pane,
`minFirst: 320`/`minSecond: 360`) — replacing the hardcoded `SizedBox(width: 420)` the code's own
comment (D45) already flagged as tuned to `entity-scrape` alone and ~95% empty for `entity-ingest`
(SCREENS §3). Each pane gained a slim frame (`_Pane` in `live_page.dart`) with a title and a ⤢
expand/restore `IconButton` — tapping either maximises that pane to the full body width, tapping
again restores the split; new `AppIcons.expand`/`.collapse` (`PhosphorIcons.arrowsOut`/`arrowsIn`).
The split stays **horizontal** (side-by-side, full height each), per SCREENS §3's own reversal of
an earlier vertical-stack proposal once the real window was observed (D97) to be landscape, not
tall-and-narrow.

**`RunSummary` dissolved from its own ~180px scrolling card into a one-line header strip.** Reused
`features/flows/flow_status.dart`'s existing `flowStatusKindOf`/`flowStatusLabel`/`flowAccent`/
`flowStatusIcon`/`flowTodayLine`/`formatFlowCountdown` (already the Flows screen's own phase/gate
vocabulary, D91-D93) rather than re-deriving a second copy of "what does this phase mean" —
`run_summary.dart`'s private `_todayLine` duplicate is gone. A new once-a-second
`StreamProvider.autoDispose` (`_secondTickProvider`, same shape as `device_bar.dart`'s 5s poll)
drives a real elapsed-run timer, only ever watched while `FlowStatusKind.running` — an idle/
waiting flow never pays for it. Elapsed comes from a new `GET /api/flow-runs/{id}` fetch in
`LiveController` (`LiveState.runStartedAt`, Prefect's own recorded start time) rather than "when
did the app first notice this run," which would drift by however long the next heartbeat took to
reach this screen. Run id and last-run detail move into a rich `AppTooltip` behind an ⓘ icon — the
same collapse-behind-a-tooltip pattern D93 already used for the Flows cards' own gate detail.
D113's click-to-filter counter chips are preserved exactly, just re-hosted as a new `_CounterChip`
(the same visual shape as `ui/status.dart`'s shared `StatusChip`, but with an `AnimatedCounter` in
place of a plain string — kept local rather than widening the shared component's API for one call
site) — the "implicit animation on counters" ARCHITECTURE §9 promised, applied to the one number in
this app that changes every few seconds while you're watching it.

**The five level `FilterChip`s collapsed into one control**, not `ui/fields.dart`'s `AppSelect` —
its `T value` shape is single-select only, and this needs several levels on at once. A local
`_LevelFilterMenu` (`MenuAnchor` + stock `CheckboxMenuButton`, `closeOnActivate: false`) gets the
same collapsed-dropdown affordance without widening a shared component's API for one call site.

**Log search is new** (`_LogSearchBar` in `log_console.dart`): a debounced (250ms, matching
`SearchField`'s existing precedent) text field showing "n of m" and stepping with `Enter`/
`Shift+Enter` (`CallbackShortcuts`, `Escape` clears) — not built on `SearchField` itself, which has
no `onSubmitted`/keyboard hook to step through matches with. Matches are counted and stepped by
*line*, not by individual occurrence within a line (a line with three hits is still one stop),
matching how a quick visual scan of a log naturally works; every occurrence still highlights inline
via a hand-rolled `TextSpan` walk (`_highlightSpans`). Jumping to an off-screen match in a
virtualized `ListView.builder` needed a two-step approximation, since items outside the viewport
aren't built and have no element to `Scrollable.ensureVisible` toward: jump to a proportional
estimate first (log lines are roughly uniform height), then correct exactly on the next frame once
the target's `GlobalKey` (grown, never rebuilt fresh, so keys stay stable across builds) has a real
context. A search in progress also suspends auto-follow-the-newest-line — the user is deliberately
reviewing a specific match, possibly well above the bottom.

**Structured (JSON-shaped) log messages now render via `MonoText`'s font instead of the body
proportional face** (`_looksStructured`: trimmed message starts with `{` or `[`) — SCREENS §3 called
out a real ingest-flow JSON blob rendering broken in the old proportional-font-only version.

**Card widths for Scrape/Follow are computed, not the three hardcoded per-flow constants** (380
scrape / 420 follow — D45; classify was already full-width and needed no change). New
`wrapCardWidth()` in `surfaces/surface_common.dart` picks a per-card width so the available width
(read via `LayoutBuilder`) holds a whole number of columns with no ragged trailing gutter, clamped
between a per-surface `minWidth`/`maxWidth`.

**The scrape before→after morph, specified in ARCHITECTURE §9 and never built (AUDIT §10), now
exists** — `ui/motion.dart`'s `AnimatedReveal` already had this exact use case in its own doc
comment, just no call site. `_ScrapeCard`'s two layouts (in-progress strip / resolved composite)
are both built, and the large card wraps whichever's current in
`AnimatedReveal(visible: true, child: KeyedSubtree(key: ValueKey(inProgress), ...))` — the key
change on `scrape.done`/`scrape.skipped` arriving is what `AnimatedSwitcher` (under `AnimatedReveal`)
detects as a swap to cross-fade, rather than an instant cut.

**`DeviceBar`'s mirror button renamed `Start mirror`/`Stop mirror`** (was bare `Start`/`Stop`) —
SCREENS §3 flagged two unscoped "Stop" buttons inches apart in the same header (the flow's own and
the mirror's) as genuinely ambiguous at a glance.

**Verified:** `flutter analyze` clean. `flutter test`: 205 passing / 206 total — the one
`shell_layout_test.dart` failure (`AppShell ... rail expanded`) reproduces identically on the
branch tip from *before* this session's changes (confirmed via `git stash`), unrelated to this
work. Eight new checks in `live_layout_test.dart`: three `wrapCardWidth` unit tests, the scrape
morph transition, log search (highlight/step/clear), a JSON-shaped log line, and two full `LivePage`
mounts — one at SCREENS §3's own measured real window size (1168×973, D97) exercising the
expand/restore round trip on both panes, one at the app's documented 1024×700 floor — plus a new
assertion in the existing `DeviceBar` test confirming the disambiguated label. `flutter build
windows --debug` succeeds. Built and started for you per rule 5 — not clicked through by Claude;
five stale prior-session instances found running were killed first and replaced with one fresh one
(D87's precedent).

**Checkpoint test (yours, per PLAN_V2.md's own V2.8 gate) — passed, 2026-08-08.** A real scrape
was watched end to end: elapsed timer, counters, the in-progress card morphing into the resolved
composite, images filling the pane's actual width, log search working, and the split dragging and
persisting across a restart; at least one other flow was also checked to confirm the computed card
widths hold up where the old hardcoded numbers were tuned only for scrape. **V2.8 accepted.** Next:
V2.10 (Library review mode).

---

## 2026-08-05 (continued) — Reduce reserve variants + counter click-to-filter, cross-repo (D113)

### D113 · Two feature requests, planned first and confirmed before implementation, landed on both clients

**Chosen:** a deliberate one-session deviation from the v2 UI sequence (mid-checkpoint at V2.8)
for two features judged high-value enough to land immediately rather than wait: (1) "Reduce
reserve" gained a second variant, and (2) the Live screen's per-flow counters became click-to-
filter controls over their adjacent result-card list. Planned via `EnterPlanMode` and confirmed
with the user (filter scope, selection mode, mobile numeric display) before any code was written.

**Reduce reserve, two variants.** The existing drain-to-target behavior stops
`entity_follow`'s pool count at exactly the reserve target
(`FOLLOW × SCRAPE_RESERVE_FACTOR`), but `entity_scrape`'s own backpressure gate needs that count
*strictly below* the target (`count < backpressure`) to unblock — landing exactly at 180 leaves
Scrape still blocked; only 179 unblocks it on the same tick. `Insta-Automate/flows/
entity_follow.py` gained a second bool parameter, `unblock_scrape`, computing
`target = reserve_target - 1 if (reduce_reserve and unblock_scrape) else reserve_target` and
using `target` (not `reserve_target`) in the loop's stop condition and log lines.
`controllers/prefect.py`'s `entity_follow_trigger` consumes a second bare command,
`reduce_reserve_unblock_scrape`, folding it into `reduce_reserve`/`force` the same way the
original command already does — chosen over adding a payload/parameter to the agent's command
schema (`CommandRequest`, `_commands` storage, `_consume`/`_pending`) for one integer, since a
second distinct command name is a one-line addition to `ia-agent`'s `KNOWN_COMMANDS` set instead
of threading a new field through three layers. Gate reason stays `"reduce_reserve"` for both
variants — no client-side status-kind logic needed to change.

**Desktop** (`core/force_run.dart::reduceReserveFlow`) shows one dialog with two `FilledButton`s
computed from live config ("Reduce to 180" / "Reduce to 179 — unblocks Scrape") instead of a
single Confirm — the button itself keeps its label and existing call sites untouched. **Mobile**
(`flow_actions.dart::reduceReserve`) stays worded-only per the user's own choice (no live
config-fetch plumbing added there) — but the first version's three-action `AlertDialog` (Cancel
plus two long-label buttons) forced Material's default `OverflowBar` into a vertical stack of
stretched, inconsistently-shaped pills on a phone-width screen, one wrapping onto two lines. Your
own screenshot caught it; fixed by moving the two choices out of `actions` into the dialog's
`content` as tappable title+subtitle option cards (`_ReduceReserveOption`), leaving only a single
"Cancel" text action — a much better fit for long labels than fighting the action-row layout.

**Counters as multi-select filters.** Classify, Follow, and Scrape's live counter chips
(`run_summary.dart`'s `_EventCounters`, ported to mobile as `flow_run_summary.dart`) are now
tappable — multi-select, not isolate-one, per your explicit choice — filtering the adjacent
result-card list to cards matching any selected key. Scan and Ingest stay non-interactive: their
cards carry no per-item verdict field to filter by. Scrape gained a new **Failed** counter
(every `scrape.skipped` reason folded into one bucket, your own call over a per-reason
breakdown) alongside the existing **Scraped**; its **Processed** stays plain since it's a
superset, not its own category. Filter state (`LiveState.selectedVerdicts` /
`FlowRunController.selectedVerdicts`) is scoped to the currently displayed run — reset wherever
`events` itself already resets on a new `run_id`, not on every WS reconnect/manual refresh. The
still-in-progress "large card" pattern (Scrape's front-and-center latest item) is deliberately
unaffected by an active filter, since an unresolved subject has no bucket to match yet.
`ui/status.dart`'s `StatusChip` gained optional `selected`/`onTap` params, additive only — every
existing static call site is unchanged; `onTap` wraps the chip in `Material`/`InkWell` only when
set. Mobile's equivalent uses the stock `FilterChip` instead of a custom component, since Flutter
already ships exactly that selection semantic.

**Verified:** a throwaway script (`check_reduce_reserve.py`, not committed) calling the real
`entity_follow.fn(...)` directly (Prefect's own engine-bypass escape hatch, D86's precedent) with
every heavy dependency (DB session, device, Instagram call, Telegram, agent HTTP) monkeypatched
against a scratch temp dir — 6/6, including the exact-stop-at-180 and exact-stop-at-179
invariants and a normal-mode-ignores-unblock_scrape case. `agent/tests/test_scheduler.py` 26/26
(25 prior + 1 new). Desktop `flutter analyze` clean, `flutter test` 197/197 (196 prior + 1 new in
`flows_layout_test.dart` asserting the real computed dialog target numbers, not just that a
dialog opened) — the one `shell_layout_test.dart` failure seen mid-session was confirmed
pre-existing on a clean `feat/v2-ui-overhaul` tip via `git stash`, unrelated to this work. Mobile
`flutter analyze` clean (the one pre-existing `thumbnail_cache.dart` lint, untouched). Deployed
for real: `Insta-Automate`'s `feat/control-center` pushed (`921551b`), `ia build`'d, both the
scheduler and worker pods restarted (the worker needed a real rebuild, not just a rollout, since
`entity_follow`'s signature changed — D86's precedent again), `ia prefect deploy` re-run for
D38's known work-pool-orphaning gap, both pods' loaded source confirmed via `kubectl exec` to
match the fixed commit. `ia-agent.exe` restarted for the new `KNOWN_COMMANDS` entry, confirmed
live via a real command POST and all three supervised services still `adopted` with uptime
intact (D87's lesson, checked again). Desktop app built and started for you, mobile APK built and
installed on the test phone, neither driven by Claude. **You tested both live, confirmed
everything worked functionally, then flagged the mobile Reduce-reserve dialog's layout — fixed
and reconfirmed live in the same session.** Session closed here on your call.

---

## 2026-08-05 (continued) — V2.5 follow-up: cap-hit false urgency and cramped nav icons (D112)

### D112 · The Overview hero stops warning on today's cap; nav rail icons enlarged

**Chosen:** Two more real issues, flagged from the same screenshots that closed out D111's
checkpoint. First, `hero_tile.dart`'s `_compute()` still put a flow sitting at today's cap into
the same "N things need attention" bucket a failed service or a down dependency uses — the
identical false-urgency shape D111 had just fixed for a standing-by flow, just a different
trigger (`atCap`/`checkCap`, reading `Burndown`, not a flow's own gate at all). The cap exists
specifically so the pipeline stops there on its own; reaching it is the cap working, not a
problem — deleted from the hero's warning computation entirely, along with the now-unused
`Burndown` parameter/`burndownProvider` watch that only ever fed it (today's caps already have
their own dedicated read in `CapsTile`). Caught in the same pass, not separately reported: the
headline's pluralization was wrong — `'${reasons.length} thing${plural ? 's' : ''} need
attention'` always said "need," so a single reason read "1 thing need attention" — fixed to
conjugate both nouns ("1 thing needs attention" / "2 things need attention").

Second, `nav_rail.dart`'s `_NavTile` icons — `IconSize.sm` (14px) with 1px of vertical margin
between tiles — read tiny and cramped against a 72px-wide collapsed rail with plenty of unused
space, smaller than the pre-V2.5 flat `NavigationRail`'s own default (18px) ever was. Bumped to
`IconSize.lg` (24px) with real padding (`tokens.space.sm`, both axes) and margin
(`tokens.space.xs` horizontal, half that vertical) around each tile, in both the expanded and
collapsed states — the `_CollapseToggle` button's own deliberately-small utility icon (16px, a
window-button-style affordance, not a nav destination) was left untouched.

**Verified:** `flutter analyze` clean; `flutter test` 197/197 (195 prior + 2 new — a
cap-hit-stays-good case and a real-dependency-down pluralization case in
`overview_layout_test.dart`, both scenarios with zero prior coverage) + a regression guard in
`shell_layout_test.dart` asserting every real nav destination icon renders at `IconSize.lg`
specifically, not just "no overflow," so this exact regression can't silently return.
`flutter build windows --debug` succeeds. Built and started for you.

**You confirmed both live and asked to close the session here.** Committed.

---

## 2026-08-05 (continued) — V2.5, Shell, plus a same-session terminology/semantics fix (D111)

### D111 · Status cluster + grouped nav rail landed; "blocked" renamed to "standing by" and stopped reading as a warning

**Chosen:** V2.5's three PLAN_V2.md bullets, each reusing an existing component rather than
inventing one: the title bar's old single-text `_StatusChip` (`'Agent: connected'`) became a
`_StatusCluster` of five `StatusDot`s (agent, k3s, postgres, prefect [`prefect-server`/
`prefect-pool` combined, worst level wins], phone) each with a rich `AppTooltip` naming the
component, its detail and its latency — reading only `connectionProvider` and
`dependenciesControllerProvider`, no new agent endpoint. A ⌘K button sits next to the existing
`?` button, **disabled** with a "coming soon" tooltip rather than wired to a placeholder
action — the palette itself is V2.12's scope, and a clickable button that does nothing would
be a worse affordance than an honestly-disabled one. The flat seven-item `NavigationRail` (no
grouping API exists in the stock widget) was replaced with a hand-built `AppNavRail`
(`shell/nav_rail.dart`) — MONITOR/OPERATE/ANALYZE groups, a `Review` sub-item under Library
jumping straight into a review folder (the same `selectedFolderProvider` mechanism V2.6/V2.7's
⚑ jumps already use), collapsible to icons-only via a new `Ctrl+B` binding persisted through
`shared_preferences` (`NavRailCollapsedNotifier`, mirroring `ThemeController`'s pattern), and
new `Ctrl+1..7` destination jumps — both live in `AppShell`'s existing `CallbackShortcuts` map
alongside the untouched `?` binding. The destination switch is wrapped in the already-existing
`PageTransition`. The faked-maximize workaround (`title_bar.dart`) is untouched, verbatim.

**A second, real correction landed the same session, from your own live read of the running
app, not a code review.** "Blocked" (`FlowStatusKind.blocked`, `_StatusKind.blocked` before
V2.6 collapsed it into one shared `flow_status.dart`) named a flow whose `gate.ok` is false —
backpressure, the daily cap, nothing queued — as if something were preventing it against its
will. It isn't: the flow doesn't need to run yet and will pick back up the moment its
condition is true again, the same way `cooldown`/`polling` already do. Renamed to
`standingBy` ("Standing by"), and — because the old name wasn't just wrong wording but wrong
*severity* — its accent moved from `StatusKind.warn` (amber) to `StatusKind.info`, the same
"still on schedule, not stuck" bucket `cooldown`/`polling` sit in. That forced a real logic
change, not just a rename: `hero_tile.dart`'s `_compute()` previously put a standing-by flow
into the same "N things need attention" warn bucket as a failed service or a dependency down —
deleted from that computation entirely, so the Overview hero now stays "All five flows running
normally" regardless of how many flows are standing by. `nav_rail.dart`'s Flows destination
lost its badge outright for the same reason — a count of resting flows isn't the kind of
actionable signal `CountBadge` exists to carry, unlike an unhealthy-service count or a real
curation backlog, so badging it under a calmer color would still have been the same false
urgency wearing a new name. `flow_card.dart` — the pre-V2.6 private duplicate of this exact
enum, orphaned dead code since `FlowCardCompact` replaced it in V2.7 (its own header comment
said as much) — was deleted rather than kept in sync by hand a second time.

**Verified:** `flutter analyze` clean; `flutter test` 195/195 (191 prior + 4 new in
`test/shell_layout_test.dart` — rail overflow expanded/collapsed at the 1024px floor, real
badge counts including the standing-by-gets-no-badge assertion, and a `Ctrl+B` round trip
through the real persisted notifier — plus 3 existing tests in `flows_layout_test.dart`/
`overview_layout_test.dart` updated to the new label/behavior rather than deleted).
`flutter build windows --debug` succeeds. Built and started for you twice (once per round),
per rule 5.

**You confirmed the shell live and flagged two more real issues from the same screenshots,
both left open for the next round rather than guessed at here:** the Overview hero still
treats a flow hitting today's cap as "needs attention" — the same false-urgency shape as
`standingBy`, just a different trigger (`atCap`, not a flow's gate at all) that this round
didn't touch; and the nav rail's icons read as too small/cramped now, needing more of the
rail's own width than the current `IconSize.sm`/tight padding give them. Committed on your
explicit "commit to this point," with those two items scoped as the immediate next work
rather than blocking this commit.

---

## 2026-08-05 (continued) — V2.9, Library browse (D110)

### D110 · Per-folder grid aspect ratio, stage-grouped rail, ResizableSplit rails, always-visible toolbar

**Chosen:** SCREENS.md §5a-0's highest-impact single Library fix landed first, in
`library_grid.dart`: a `folder → aspectRatio` map (`libraryFolderAspectRatio`,
`core/library_models.dart`) drives `SliverGridDelegateWithFixedCrossAxisCount
.childAspectRatio` instead of a hardcoded `1` — row-crop folders (`scanned`, `gender_valid`,
`gender_invalid`, `scrape_queued`) now lay out as a real 5.45:1 strip and full-page folders
(`entities`, `scraped`, `follow_queued`) as a real 1:2.08 portrait, instead of both wasting
40–82% of every near-square cell. The keyboard/scroll-into-view row-height math
(`_scrollToIndex`'s `rowStep`) was updated alongside — it had assumed square cells (`width ==
height`) throughout, which the aspect-ratio fix would otherwise have silently broken.
`BoxFit.contain` (D41) untouched. `FolderRail` is now stage-grouped (`libraryStageGroups`:
INTAKE / SCANNING / ⚑ YOUR REVIEW / QUEUED) instead of seven undifferentiated rows, marking
`gender_valid`/`scraped` as the two folders that are actually the user's job. Both rails
(`library_page.dart`) are nested `ResizableSplit`s now, replacing fixed 220px `SizedBox`
columns — `persistKey`s `library.rail.folders`/`library.rail.entities`, the hardcoded 220
becoming just the first-run default. `LibraryToolbar`'s Apply/Delete are always rendered,
disabled (not absent) with an empty selection — "never hide a screen's primary action."
Counts go through a new shared `plural()` helper (`core/plural.dart`) instead of each
call site's own string surgery, rendered via `NumericText`. The grid gets a real skeleton
loading state (`_GridSkeleton`) shaped to the folder's own aspect ratio and approximate
column count, rather than a bare spinner. **D48's selection mechanics (plain click/Space
toggles, arrows move focus only, Shift ranges) were not touched** — the only change inside
`library_grid.dart`'s keyboard handling is the row-height arithmetic feeding the existing,
unchanged `moveFocus`/`selectRange`/`toggle` calls.

**A real test-authoring pitfall caught while extending `library_layout_test.dart`, not a
production bug**: two new tests originally called `_render` (which calls `tester.pumpWidget`)
twice within one `testWidgets` block, expecting the second call to fully replace the first —
but `MaterialApp`/`Scaffold`/`ProviderScope` all being the same types at the same tree
position means Flutter/Riverpod reuse the existing `Element`/`ProviderContainer` across the
second `pumpWidget` rather than tearing down and rebuilding from scratch, so the second
render's overrides never actually took effect and both tests silently asserted against the
*first* render's state. Both failures were exactly that shape (a "selected" toolbar case still
showing the disabled buttons from the empty-selection render; a portrait-folder assertion
still measuring the previous strip-folder's tile size) — fixed by splitting each into two
independent `testWidgets` blocks, matching this file's own existing one-render-per-test
convention throughout.

**Verified:** `flutter analyze` clean; `flutter test` 191/191 (186 prior + 5 new in
`library_layout_test.dart`: stage-grouped rail with the ⚑ marker, Apply/Delete
disabled-then-enabled across a selection change, and real measured tile dimensions for both a
row-crop and a full-page folder). `flutter build windows --debug` succeeds. Built and started
for you per rule 5; `ResizableSplit`'s own drag/persist behavior already has generic coverage
in `ui/layout_test.dart` (D100), not re-tested here.

**You tested live and confirmed it — rails drag and persist, Apply/Delete visible-but-disabled
with nothing selected, selection unchanged, counts match, and the row-crop folders visibly fit
far more images per screen.** Committed.

---

## 2026-08-05 (continued) — V2.7, Overview bento, built and live-bug-fixed (D109)

### D109 · Overview rebuilt as a bento grid; two more latent shared-component bugs found

**Chosen:** `overview_page.dart` replaces the old vertical stack of five full `FlowCard`s, two
cards, five 340px `fl_chart` burn-down cards and two more cards (AUDIT §12) with a `HeroTile`
(one computed status sentence, `StatusKind`-driven accent, up to two actions) above a real bento
grid (SCREENS.md §1): `PipelineStrip` (five new `FlowCardCompact` tiles — status dot, name,
one-line state, no controls — connected by the same live backlog counts V2.6's `PipelineEdge`
reads), a new `CurationTile` (the two human-review backlogs, clickable into Library), a new
`CapsTile` (progress bars + `Sparkline`s replacing the five big charts — full history stays on
Insights), and the existing Services/Dependencies/Device/Recent widgets reused, tightened for
tile width. Three real breakpoints (`_bentoFor`, DESIGN_SYSTEM §7's `compact <1100` /
`medium 1100–1500` / `wide ≥1500`) rearrange the same eight tiles rather than one fixed layout
overflowing at the 1024px floor. `HeroTile`'s priority, worst first: agent disconnected → bad;
any service failed → bad; any flow blocked, any dependency down, any cap hit → warn; otherwise →
good ("All five flows running normally") — all read from the exact providers their own screens
already use, no new agent endpoints.

**Two more real bugs found live, same pattern as V2.6's `AppPanel.accentEdge` crash — a shared
V2.2 component getting its first real call site.** `Sparkline` (`ui/data.dart`) threw
`type '(num, num) => num' is not a subtype of type '(int, int) => int' of 'combine'` on every
render: `values`/`cap` are declared `List<num>`/`num?`, but every real caller passes concrete
`List<int>`/`int?` (Dart generics are reified per-object), and calling `.reduce()` directly on
the field resolves the method's generic signature against the *object's* real `int` type
parameter, not the `num`-typed field it's stored in — a `(num, num) => num` closure then fails
the runtime subtype check. No prior `Sparkline` call site existed to catch this; `data_test.dart`
only ever covered `AppTable`. Fixed by normalizing to a genuine `List<double>` up front in
`_SparklinePainter.paint()` (a leaf type, not further subtyped) rather than operating on the
declared-but-misleading `List<num>`. Separately, `DependencyStrip` and `DeviceBar` — both
previously only ever embedded in roomy half-width sections — overflowed once placed in
Overview's narrower tiles: `_DependencyChip`'s label had `maxLines: 1` + ellipsis but no actual
width bound to ellipsize against (a `Wrap` never constrains a single child narrower than its own
natural size), fixed with a `ConstrainedBox(maxWidth: 130)`; `DeviceBar`'s device-name
`ConstrainedBox(maxWidth: 140)` alone doesn't shrink below its cap when the *row* itself is too
narrow, fixed by wrapping it in `Flexible` (a no-op in the roomier Live header, where D46's
tuning is untouched).

**Live-tested, one round.** You confirmed the hero tile, pipeline, caps, curation counts and
dependencies/services/device tiles all correct, with one minor note: the page needed "a little
scroll" at your real window size rather than sitting fully above the fold. Tightened in response
— the hero→grid gap (`Gap.xl` → `Gap.lg`) and `RecentNotificationsCard`'s Overview instance
(`maxShown` 3 → 2) — not separately re-verified live, a small enough change to ship with the
rest rather than hold up the commit for a second screenshot round.

**Verified:** `flutter analyze` clean throughout; `flutter test` 186/186 (179 prior + 9 new
`overview_layout_test.dart` cases: the full-data layout at all three breakpoints — 1024/1300/1700px
— the empty state, and all four `HeroTile` `StatusKind`s including the disconnected-beats-
everything-else priority and the curation-waiting action appearing independent of hero kind).
`flutter build windows --debug` succeeds. Built and restarted for you twice (initial build, the
scroll tightening) per rule 5.

---

## 2026-08-05 (continued) — V2.6, Flows pipeline, built and live-bug-fixed (D108)

### D108 · Flows rebuilt as a vertical pipeline; a real cross-theme crash and an alignment bug found and fixed live

**Chosen:** `flows_page.dart` is now five `FlowNode` strips connected by four `PipelineEdge`
connectors (SCREENS.md §2), replacing the old five-card `Wrap`. Edges read live backlog counts
from `libraryFoldersControllerProvider` (`entities/`, `scanned/`, `gender_valid/`, `scraped/`) —
no agent work, per the scope boundary. The two ⚑ human-review edges (`gender_valid/` → Scrape,
`scraped/` → Follow) jump straight into that Library folder on click, reusing
`selectedFolderProvider`/`selectedNavIndexProvider`. The edge into Follow turns `warn` when
`scraped + follow_queued` exceeds `FOLLOW × SCRAPE_RESERVE_FACTOR` — the same math
`reduceReserveFlow` already computes, now visible on the pipeline itself rather than only
explained after the fact. All six D84 `_StatusKind` states and their derivation are re-derived
verbatim in a new shared `flow_status.dart` rather than touched in `flow_card.dart` — that file,
and `overview_page.dart`'s use of it, is deliberately untouched, since V2.7 is what replaces it
with `FlowCardCompact`, not this checkpoint. The 56px cooldown ring is gone: a compact inline
`mm:ss` next to the status word plus a thin determinate progress line along the node's bottom
edge — still the *only* state with a countdown. Blocked flows show their raw gate detail inline
now (D93 had to hide it behind a hover; the node layout has room), and a new click-to-expand
accordion (`expandedFlowProvider`, one node open at a time) reveals last-run detail, full
counters, the raw gate string, View logs and Open in Live — View logs itself moved off the
collapsed row into a per-node overflow menu to free space. Every button's semantics (D88's
Trigger now, D86's Reduce reserve, D69's Stop) and confirm dialogs are unchanged.

**Found live, not in review — two real bugs, both fixed the same session.**

**1. A genuine crash, blank on every theme but Classic.** The user's first screenshot showed
Classic looking cluttered but working; the second, on Command Deck, showed every `FlowNode` as a
completely empty box — no text, no icons, no switch — while the surrounding `PipelineEdge` rows
rendered fine. Root cause, confirmed by pumping `FlowNode` against all six themes directly rather
than guessing: `ui/surfaces.dart`'s `AppPanel` had never had a real `accentEdge` call site before
this checkpoint (`FlowNode` is the first), and building a rounded `Border` with the accent edge as
one colored side and the other three sides a different color throws
`"A borderRadius can only be given on borders with uniform colors"` — but only for a theme whose
`DepthStrategy` actually paints a border (Command Deck, Mica). Classic's shadow-only strategy
means its "plain" sides are all `BorderSide.none`, which happens not to trigger the check, so the
bug shipped invisibly until a theme with `DepthStrategy.border` exercised it. **Fixed in the
shared component**, not worked around per call site: `accentEdge` is now painted as a separately
`ClipRRect`-clipped overlay bar on the left, matching the panel's own corner radius, instead of
being folded into the `Border`. Verified directly: a throwaway test pumping `FlowNode` under all
six themes' real built `ThemeData` (not the bare-`ThemeData()` fallback path the existing
`surfaces_test.dart` accentEdge case happened to use, which is exactly why it never caught this)
confirmed zero exceptions post-fix, then deleted.

**2. Switches and buttons weren't in a straight column.** The state label next to the switch was
a `Flexible` (sizes to its own text), so the switch's x-position drifted left/right on every row
depending on that row's label length, and the per-node overflow menu (only present when a
`lastRun` exists) shifted it further depending on which rows had one. Fixed: the label is now
`Expanded` (fills the leftover space and right-aligns within it) and the overflow menu slot is
always reserved at a fixed width, present or not — both together give every row's switch the same
fixed distance from the right edge. Then the action-button row (Trigger now / Reduce reserve /
Stop), previously flush-left under the icon gutter, was moved to right-align under that same
column, matching SCREENS.md §2's own mockup positioning rather than the improvised left-flush
placement this session's first draft used. A naive `Row(mainAxisAlignment: end, children:
[ButtonGroup(...)])` regressed the D87 three-button wrap regression test — a bare `Row` gives its
lone child unbounded width, so the inner `Wrap` never wraps and overflows instead — fixed with a
bounded `SizedBox(width: double.infinity)` around a raw `Wrap(alignment: end)` (bypassing
`ButtonGroup`, which has no alignment parameter).

**Rejected:** leaving `accentEdge` un-load-bearing (reverting `FlowNode` to no accent edge) rather
than fixing `AppPanel` — rejected because `accentEdge` is COMPONENTS.md's documented mechanism for
exactly this ("how a failed service, a blocked flow or an errored ops job announces itself"), and
Services (V2.11) is already planned to be its second consumer; leaving the shared component broken
would just relocate the same crash there later.

**Verified:** `flutter analyze` clean throughout; `flutter test` 179/179 (166 prior + 13 new in
the rewritten `flows_layout_test.dart`, covering all six `_StatusKind` states, the inline blocked
gate detail, the cooldown progress line, the entity-follow three-button case at a narrow 360px
width — D87's own regression scenario, now against the new layout — the expansion accordion, and
both `PipelineEdge` variants including the ⚑ review-folder jump). `flutter build windows --debug`
succeeds. Built and restarted for you three times across the session (initial build, the crash
fix, the alignment fix) per rule 5 — not clicked through by Claude. **You tested live each round**:
round 1 caught the cross-theme crash from your own Command Deck screenshot; round 2 confirmed the
crash was gone and flagged the switch/button misalignment from your Classic screenshot; round 3 was the alignment fix above, after which **you said to proceed** — taken as the
checkpoint test passing. Committed.

---

## 2026-08-05 (continued) — V2.5–V2.12 split into visual-first, functional-second (D107)

### D107 · Remaining v2 checkpoints grouped and reordered: visual before functional

**Chosen, at the user's request, once V2.4/D106 closed out:** PLAN_V2.md originally left
V2.5–V2.12 as "independent, reorder freely." Grouped instead:

- **Visual** (redesigns how something already works looks or is organized — no new
  capability): V2.6 (Flows pipeline), V2.7 (Overview bento), V2.9 (Library browse), V2.5
  (Shell), V2.8 (Live).
- **Functional** (adds a genuinely new interaction): V2.10 (Library review mode — the
  headline feature of all of v2), V2.12 (Command palette — `Ctrl+K` doesn't exist at all
  today), V2.11 (Services/Insights/Settings — real new capabilities, terminal search/copy/
  font-size, resizable panes, but the least load-bearing of the three).

**Execution order: V2.6 → V2.7 → V2.9 → V2.5 → V2.8 → V2.10 → V2.12 → V2.11 → V2.13.** Within
each group, ordered by impact per PLAN_V2's own existing "most transformative"/"highest-
impact" language rather than re-litigated from scratch. V2.10's existing dependency on V2.9
falls out of the order for free. V2.13 (motion/accessibility/release) stays last regardless —
it audits whatever V2.5–V2.12 produce, so there's nothing for it to check before they're done.

**Why:** the user's own framing — get the app looking finished across every screen first,
*then* layer new interactions on top of a finished look, rather than the reverse (a
functionally richer but visually half-migrated app partway through).

**Rejected:** leaving the original "reorder freely" note as-is (too vague to actually commit
to an order) and a strict alternating visual/functional interleave (rejected as arbitrary —
grouping cleanly is more legible than alternating for its own sake).

PLAN_V2.md's "Sequencing notes" section rewritten to match; nothing about any individual
checkpoint's own scope (its own `## V2.n` section) changed — only which one comes next.

---

## 2026-08-05 (continued) — post-commit follow-ups: canvas background bug, density independence (D106)

### D106 · `AppShell`'s Scaffold background was hardcoded transparent; Command Deck's density nudge removed

**Two separate fixes, found live after V2.4 (D103–D105) was already committed.**

**The real one — the page background never actually changed theme.** `shell/app_shell.dart`'s
root `Scaffold` had `backgroundColor: Colors.transparent` hardcoded, predating the entire v2
token system. For Classic and Mica that's correct by coincidence (both really do want a
transparent canvas so the native Mica-blurred desktop shows through) — but it meant the other
four themes' own opaque `surface.canvas` value (Command Deck's `#07080B`, Nocturne's `#13131A`,
Daylight's `#FBFBF9`, Swiss's `#FFFFFF`) was never painted at all. The visible page background
stayed whatever was behind the window regardless of theme, while cards correctly went dark
(post-D104) — the mismatch the user described as "the widgets look way darker... the app looks
different" when switching to Command Deck: the cards were right, the backdrop around them
wasn't moving. Fixed by reading `Theme.of(context).tokens.surface.canvas` instead of the
hardcoded literal — a no-op for Classic/Mica (their token *is* `Colors.transparent`, so the
pixel output is identical), a real fix for the other four.

**Command Deck's "ships compact by default" density nudge (D103) removed outright, at the
user's explicit request.** THEMES.md §2 describes Command Deck as *designed for* `compact`, but
auto-applying that on selection meant density silently moved without the user asking it to —
exactly the kind of state a user expects to stay put until they change it themselves,
regardless of which theme they're on. `ThemeController.setTheme()` no longer touches density at
all; THEMES.md and DESIGN_SYSTEM.md's density table reworded from "ships compact by default" to
"designed for compact," since the theme's own token values are unchanged — only the automatic
behavior is gone.

**Verified:** `flutter analyze` clean, `flutter test` 175/175 unchanged (no test asserted the
old Scaffold background or the density nudge). Rebuilt; two stale instances found running (not
just the expected one — cleaned up along with the intended restart) and replaced with a single
fresh one, started for you per rule 5.

**The background fix confirmed live** — a follow-up screenshot of Command Deck shows the page
background and cards finally reading as one coherent near-black-blue surface, no more mismatch.
The density-independence half wasn't separately re-verified this round (no theme switch was
shown after it) — worth an explicit check next session. Same session, one more small thing
spotted while looking at the fixed Command Deck screenshot: `flow_card.dart`'s cooldown countdown ring
(`_FlowStatusIndicator`) centered its `NumericText` directly against the ring's stroke with no
gap, tightest on the `h:mm:ss` case (past an hour). Added `Padding(EdgeInsets.all(3))` around
just that text — scoped to the countdown branch only, not the shared `_size`/`_iconBadge()` used
by every other flow state, so this doesn't change the size of any of the non-cooldown icon
badges. `flutter analyze` clean, `flutter test` 175/175 (`flows_layout_test.dart`'s cooldown
case unchanged, still green). Rebuilt, restarted for you.

**The padding alone wasn't enough — caught immediately by a real side-by-side screenshot,
before the session closed.** Two flows cooling down at once: Scrape's `9:33` (4 chars, under an
hour) had room to spare inside the padded ring; Follow's `14:16` (5 chars, further into the
wait) still crowded the stroke. The padding treated the symptom per-string; the actual limiter
is the ring's own diameter against the *widest* case the format string can produce
(`h:mm:ss`, 7 chars, past an hour) — a 3px pad can't fix a ring that's simply too small for
that width. Fixed properly this time: `_size` (`_FlowStatusIndicator`'s shared box, also used
by `_iconBadge()` for every non-cooldown state) raised from 56 to 64. Deliberately kept shared
rather than special-cased to the cooldown branch alone — a flow's indicator changing size the
moment it flips in or out of cooldown would be its own small visual glitch. Verified:
`flutter analyze` clean, `flutter test` 175/175, including `flows_layout_test.dart` and
`overview_layout_test.dart` (which embeds `FlowCard` per D79) at the 1024px floor — the one
place a few extra pixels on a shared widget could have shown up as a real overflow. Rebuilt,
restarted for you.

**Still didn't match — the real gap wasn't the diameter at all, it was that a bare ring has no
fill.** Your side-by-side screenshot of the 64px version showed the countdown ring still
reading noticeably smaller than the icon badge next to it, same bounding box or not.
Root cause: `_iconBadge()` paints a *solid* tinted disc (`Container` with a `BoxShape.circle`
fill) — full visual weight across the whole `_size` footprint. `CircularProgressIndicator`
only ever paints a thin stroke; its `backgroundColor` parameter draws a second, fainter stroke
for the *remaining* track, not a fill — so the cooldown case had nothing but two thin
concentric rings on an otherwise empty background, which reads as meaningfully smaller than a
filled disc even at an identical bounding box (real perceptual size, not a pixel-measurement
bug — matches the user's own framing, "match the ring size with the icon radius," once actually
compared side by side). Fixed by giving the cooldown `Stack` the exact same tinted-disc
`Container` `_iconBadge()` uses as its base layer, with the progress ring drawn on top and its
own `backgroundColor` set to `Colors.transparent` (a second faint track over a solid fill would
have just looked muddy). `_size` stays 64 — the fill was the actual fix, not a further size
bump. Verified: `flutter analyze` clean, `flutter test` 175/175 unchanged. Rebuilt, restarted
for you.

**Still the same ring size, even with the fill — because the fill was never the whole story.**
Your follow-up screenshot showed exactly what the disc-fill fix predicted it would (a correctly
64px tinted backdrop), but the *ring itself* — the arc that actually counts down — was
unchanged from every earlier attempt, small, sitting in the middle of the now-larger disc with
a visible gap. The real, final root cause, found by actually reasoning through
`CircularProgressIndicator`'s own layout algorithm rather than assuming it behaves like the
`Container` next to it: a plain decorated `Container` with no explicit size, given *bounded*
constraints (which is what a `SizedBox`-constrained `Stack` hands each loose child), tries to
be **as big as possible** — that's why the backdrop disc has always correctly filled `_size`.
`CircularProgressIndicator` does not follow that rule. Its render object computes a **fixed**
~36px preferred diameter regardless of the bounded space available, and merely clamps it if the
available space is *smaller* — it never grows to fill a *larger* available space the way a
`Container` does. This is why raising `_size` from 56 to 64 (the second attempt) changed
nothing about the ring itself: `_size` was only ever reaching the `Stack`'s bounding box and the
backdrop disc, never the ring, because the ring was never given a tight size of its own — it
was sitting loose inside `TweenAnimationBuilder` inside the `Stack`, silently rendering at its
own ~36px default the entire time, through every previous attempt in this session. Fixed for
real this time: the `CircularProgressIndicator` (via its `TweenAnimationBuilder` wrapper) is
now wrapped in an explicit `SizedBox(width: _size, height: _size)`, giving it the *tight*
constraint its layout algorithm actually needs to grow. Verified: `flutter analyze` clean,
`flutter test` 175/175 unchanged (no existing test measured the ring's actual rendered
diameter — a real gap in coverage for this specific class of bug, left as-is rather than
building a new test for one bugfix this late in the session). Rebuilt, restarted for you —
**not yet seen live**, session closing here; the next session should confirm this — the ring's
arc itself, not just its backdrop, should now visibly match the icon badges — plus the
still-open D106 item (density independence across a theme switch) before moving on to V2.5.

**One more, cosmetic, once the 64px ring was actually visible:** the countdown text itself
(`13:55`) looked small against the now-correctly-sized ring. `NumericText`'s role bumped from
`micro` (10.5) to `caption` (12) — both use the same muted color already, `caption` just isn't
bold and drops `micro`'s loose letter-tracking, so this is a straightforward size increase, not
a style change. `flutter analyze` clean, `flutter test` 175/175 unchanged. Rebuilt, restarted
for you.

**Final round: the user asked to tune the ring size themselves rather than iterate through
Claude again, and found `_size` coupled the ring to every icon badge — a real design gap in the
fix above, not just a missing knob.** `_size` was shared by design (so an indicator's footprint
never shifts when a flow flips in/out of cooldown), but that meant the *only* way to resize the
ring was to also resize `_iconBadge()`'s circle for every other flow state — not what "let me
tune the ring" means. Split into two constants: `_size` (64, unchanged — the outer bounding box
and every non-cooldown icon badge) and a new `_ringSize` (the backdrop disc + progress arc
only), centered inside the same `_size` box via the `Stack`'s existing `alignment: center`, so
nothing about the row layout moves regardless of what `_ringSize` is set to. Pointed the user at
the exact line rather than continuing to guess-and-check; **the user landed on `_ringSize = 48`**
themselves. `flutter analyze` clean, `flutter test` 175/175. This is the version committed
below.

---

## 2026-08-05 (continued) — a third density tier, requested mid-retest (D105)

### D105 · `Density` gains `spacious`, above `comfortable`

**Chosen:** a third tier above the default — `compact` (0.75×/0.95×) < `comfortable`
(1.0×/1.0×) < `spacious` (1.15×/1.05×), the user's own framing ("low/medium/high, where
compact is low and comfortable is medium"). Kept the existing `compact`/`comfortable` names
rather than renaming everything to `low`/`medium`/`high` — both are already load-bearing
vocabulary across THEMES.md, DESIGN_SYSTEM.md, PLAN_V2.md's V2.4 checkpoint text, and
`theme_controller.dart`'s Command Deck density nudge; a rename would be pure churn for a
request that's really just "add a third option, roomier than today's default."
`build_theme.dart`'s `_applyDensity` early-return switched from `density ==
Density.comfortable` to checking both scale factors equal `1.0`, so it stays correct
regardless of which named tier happens to be the identity one. Settings → Appearance's
segmented control now shows all three, ordered low→high. `flutter analyze` clean, `flutter
test` 175/175 unchanged (no test asserted a two-tier `Density`). DESIGN_SYSTEM.md §1.8 and
THEMES.md §9 updated to match. Rebuilt, stale instance killed, fresh one started for you per
rule 5 — not clicked through by Claude.

---

## 2026-08-05 (continued) — a real V2.1-era bug found live retesting D103 (D104)

### D104 · `AppTokens.type` collided with `ThemeExtension.type`, silently pinning every screen to Classic since V2.1

**Found by you, immediately, the first time a second theme actually existed to diverge from
the fallback.** Your screenshot of Overview under Swiss showed the split precisely: switches,
the selected nav label, "View logs" — all correctly red (Swiss's `accent.primary`). Every card
background — Flows, Services, Dependencies — still Classic's dark near-black. Not a partial
render, not a Swiss-specific bug: every theme, everywhere `Theme.of(context).tokens` is read
directly.

**Root cause:** `AppTokens` (`tokens.dart`, written in V2.1) declared `required this.type` as
its `TypographyTokens` field, with `@override` on top of `ThemeExtension<T>`'s own `Object get
type => T` getter — reasoned at the time as "a valid narrowing override, just needs the
annotation" (true, syntactically). What that comment missed: `type` isn't decorative on
`ThemeExtension`. Flutter's `ThemeData` constructor uses it as the map key when converting the
`extensions: [...]` list into `Map<Object, ThemeExtension>` — so `ThemeData(extensions:
[tokens])` was keying itself by a `TypographyTokens` *instance* instead of the `AppTokens` Type
object. `Theme.of(context).extension<AppTokens>()` — which looks up by the real `AppTokens`
type — missed on every single call, and `AppTokensX.tokens`'s `?? buildClassicTokens()`
fallback fired unconditionally, for every theme, every time.

**Invisible through V2.1, V2.2 and V2.3's own checkpoint tests — not because they were
insufficiently thorough, but because the bug was structurally unobservable until a second
theme existed.** Classic was the only theme through all three checkpoints; the fallback
(`buildClassicTokens()`) and the real intended value were identical, so nothing anywhere could
tell them apart. Confirmed directly: an isolated widget-test probe (`MaterialApp(theme:
buildTheme(buildSwissTokens())), home: AppCard(...)`) rendered the card at Classic's dark
`surfaceContainer`, not Swiss's white `surface.base` — reproduced with zero Riverpod, zero
`app.dart`, zero animation involved, before touching any fix.

**Fixed:** the field renamed `AppTokens.typography` (not `type`), the incorrect `@override`
removed — `ThemeExtension`'s own default `type` implementation (returning the real `AppTokens`
type object) is what should have been there all along. Every `tokens.type.*` read across the
codebase (11 files: `build_theme.dart`, `ui/text.dart`, `ui/status.dart`, `ui/icons.dart`,
`ui/overlays.dart`, `service_terminal.dart`, `burndown_chart.dart`, `funnel_stage.dart`,
`shortcuts_reference.dart`, `config_file_bar.dart`, plus every `themes/*.dart` constructor call)
renamed to `tokens.typography.*`. DESIGN_SYSTEM.md's own `AppTokens` code snippet — which
specified the colliding field name in the first place — corrected, with a new paragraph
explaining why `type` can never be reused as a field name on a `ThemeExtension` subclass.

**New permanent regression test, `test/theme_extension_lookup_test.dart`** — the one check the
entire rest of the suite structurally could not perform. It renders a real widget under each of
the six themes and asserts `Theme.of(context).tokens.id` actually matches, catching exactly
this class of "the fallback silently substituted itself" bug for any future field that
accidentally shadows something `ThemeExtension`/`ThemeData` relies on internally.

**Verified:** the isolated probe test that reproduced the bug was rerun unchanged after the fix
— `AppCard` under Swiss now renders `#FFFFFF`, both statically and after a real `AnimatedTheme`
swap-and-settle. `flutter analyze` clean, `flutter test` 175/175 (169 prior + 6 new in
`theme_extension_lookup_test.dart`, one per theme). Rebuilt, stale instance killed, fresh one
started for you per rule 5 — not clicked through by Claude. **Still awaiting your six-part
checkpoint test** — this fix is what that test exists to have caught, and it's the reason the
first attempt is being retested rather than committed as-is.

---

## 2026-08-05 (continued) — V2.4 Theme catalog built (D103), awaiting checkpoint test

### D103 · Five new themes, real `AppTokens.lerp`, the Appearance tab, native Mica handling, two contrast fixes

**Built, not yet committed** — rule 4: the checkpoint test (six parts, PLAN_V2.md's V2.4 section)
runs before the commit, same as every other v2 checkpoint. `flutter analyze` clean, `flutter test`
169/169 (was 167 pre-V2.4; `test/theme_contrast_test.dart` adds 48 checks — 6 themes × 8 columns
from THEMES.md §7's table — the other 121 unchanged), `flutter build windows --debug` succeeds.

**`themes/{command_deck,nocturne,mica,daylight,swiss}.dart`** transcribe THEMES.md §2–6's values
directly, deriving only what the doc left unspecified (chart.grid/axis/axisLabel/capLine —
Classic's own precedent for the same gap; Nocturne/Mica's shadowSm/shadowLg, scaled from the one
size THEMES.md did give). `registry.dart` grew to all six.

**Two of THEMES.md §7's own "computed, not measured" values failed the real contrast test and
were adjusted, exactly as the doc asks:** Nocturne's `content.tertiary` (`#565F89`, 2.76:1 against
`surface.base` — under the 3:1 UI-boundary floor) lightened to `#6A7399` (3.68:1), same muted
blue-grey family. Swiss's `status.warn` (`#C25E00`, 4.29:1 against white — under the 4.5:1 body
floor) darkened to `#B05300` (5.14:1), same hue. Both found by `test/theme_contrast_test.dart`,
parameterized over all six themes × `StatusTokens`' four states × `ContentTokens`' three levels,
plus `accent.primary` (THEMES.md §7's table has its own column for it, used for focus rings/
selection — a UI boundary, floor 3:1 not 4.5:1). Translucent tokens (Mica's whole surface stack;
`content.tertiary` in every dark theme, deliberately per THEMES.md §7's closing note) are
flattened against black/white by the theme's own brightness before measuring — a raw translucent
color's own luminance doesn't describe what's actually on screen once it's painted over a panel.

**`AppTokens.lerp` does real per-field interpolation**, replacing the `t < 0.5` snap V2.1 shipped
as a documented placeholder. Every `Color` and every `double` sweeps (new `.lerp` statics on each
sub-token class); what can't mean anything at a halfway point — face names, `DepthStrategy` and
its shadow lists, `Curve`s, `id`/`name`/`tagline` — snaps at the midpoint instead, each documented
at its own call site. `chart.series` lerps index-aligned rather than snapping: every shipping
theme's list is the same length (six), so a running burn-down chart doesn't jump mid-animation.
`MaterialApp` already wraps its child in `AnimatedTheme` and calls `ThemeData.lerp` (which finds
and lerps matching `ThemeExtension`s automatically) on every `theme:` change — `app.dart` only
needed to set `themeAnimationDuration`/`Curve` from the *incoming* theme's own `motion.slow`/
`enter` tokens (zero under reduced motion) for the crossfade DESIGN_SYSTEM §8 describes to exist
at all.

**Mica's native `Window.setEffect` hard-cut (DESIGN_SYSTEM §8) is handled by always keeping the
compositor on `WindowEffect.mica`, only ever changing the `dark` flag.** Every other theme's
`surface.canvas` is fully opaque (alpha 1.0), so which native material is running underneath is
visually moot for them regardless — Flutter's own opaque paint covers it either way, matching
what `main.dart` has done unconditionally since CP 0.2. This avoids a `solid`-vs-`mica` branch
that would have needed extra care to not regress Classic's already-accepted (V2.1 checkpoint,
pixel-identical) transparent-canvas-over-Mica look. `theme_controller.dart` calls it once on load
and once per `setTheme()`; redundant calls between two non-Mica themes are harmless (same `dark`
target, rare user action, not a hot path).

**Command Deck nudges density to `compact` on selection** (THEMES.md §2: "the one theme that
ships compact by default"), but only on the way *in* — reselecting it while already active, or
manually flipping back to `comfortable` while on it, isn't overridden. Theme and density stay two
independent, independently-persisted settings; this is a one-time default nudge, not a link
between them.

**Mica's system fonts (Segoe UI Variable, Cascadia Mono) ship with no `fontFamilyFallback`
wiring**, despite THEMES.md §4 describing one — a real scope cut. Threading fallback lists through
would touch `TypographyTokens`' schema (all six themes), `build_theme.dart`'s `_textTheme`, *and*
`ui/text.dart`'s `MonoText`/`NumericText` (which set `fontFamily` directly, bypassing
`ThemeData.textTheme` entirely) for a font pairing guaranteed present on the one OS this app runs
on. Revisit if this app is ever expected to run somewhere Segoe UI Variable/Cascadia Mono aren't
guaranteed.

**Terminal palette override (`ThemeController.setTerminalOverride`)** is implemented as a token
substitution in `app.dart` — `rawTokens.copyWith(terminal: TerminalPalette.dark)` before
`buildTheme()` — rather than touching `service_terminal.dart` at all, since every terminal call
site already reads `theme.tokens.terminal` and nothing else. `TerminalPalette` gained `.light`
(GitHub Light, per THEMES.md §8 — already cleared live against a real streaming service in
OBSERVED §6, so this is a genuine second home rather than an untested guess) and a `copyWith` so
Command Deck/Mica/Swiss can recolor two or three fields instead of respelling all 23.

**Settings gained a sixth "Appearance" tab** (before Ops, per THEMES.md §9) — a theme grid whose
cards each wrap a real miniature app-chrome subtree in `Theme(data: buildTheme(tokens))` (title
bar strip, three nav icons at the theme's own icon weight, a real `StatusDot`/`NumericText` card)
rather than a color swatch, plus `Density`/`ReduceMotionSetting`/`TerminalOverride` segmented
controls. `theme_controller.dart` mirrors `MutedTagsController`'s exact `shared_preferences`
pattern (`features/notifications/notification_controller.dart`) — a synchronous `ThemePrefs.
initial` (Classic/comfortable/auto/followTheme, matching THEMES.md §1's confirmed default) so the
first frame never flashes an arbitrary theme, corrected a moment later once the real persisted
value loads.

**Not yet exercised live** — same standing precedent as every other checkpoint's hand-off: built,
analyzed, tested, started, and handed over per rule 5, not clicked through by Claude. The six-part
checkpoint test (switch through all six themes; walk every screen in Daylight; confirm Mica shows
the desktop through the chrome; check the Services terminal in Daylight/Swiss for ANSI legibility;
toggle compact density; confirm theme+density persist across a restart) is what's outstanding
before this commits.

---

## 2026-08-05 (continued) — V2.3 migration finished (D102 · part 2 of 2)

### D102 · All 90 files under `features/`, `shell/`, `core/` migrated; the three acceptance greps enforced; token_coverage_test.dart written

**Scope closed out from D101's split.** Every screen's `Page` widget now wraps in `AppPage` —
Settings, Services, Flows, Overview, Live, Library, Insights all gained a real title (several,
per AUDIT §4, had none at all) and a single page-padding convention, replacing the six different
paddings AUDIT §3 catalogued. `EdgeInsets` literals across `features/` were swept to
`tokens.space.*`: zero raw numeric `EdgeInsets.all(16)`-shaped literals remain anywhere under
`features/` (verified by grep) — every occurrence is now either `EdgeInsets.zero`,
`tokens.space.*`-derived, or absorbed entirely into `AppCard`/`AppPanel`'s own default padding
(dropping the wrapper `Padding` outright wherever the value matched the token default). The raw
occurrence count of the word `EdgeInsets` itself only drops from 138 to 95, not to zero — Gap only
inserts space between siblings, it has no way to express a container's own inset, so a `Padding`
around a `TextField`'s decoration, a `GridView`'s content margin, or an asymmetric corner case
still writes `EdgeInsets.symmetric(...)`/`.only(...)`, now always token-sourced rather than a
magic number. `Icon(Icons.*)` widgets are fully gone from `features/`/`shell/` (verified by
grep — the only remaining hits are `FilledButton.tonalIcon` and `trayManager.setIcon`, both false
matches on the substring); every one is `AppIcon(AppIcons.*)`. Numeric displays route through
`NumericText` at every site COMPONENTS.md §2 named by file:line (the cooldown ring, today's
counters, run-summary counters, the ranking table's three metric columns, library folder counts)
plus the further ones found doing this pass (log console timestamps, the pairing code, dependency
latencies, the funnel/burn-down chart numbers). `Gap.xs/.sm/.md/.lg/.xl` replaces bare
`SizedBox(height/width: N)` wherever the value maps onto the five-step scale.

**`AppIcons` grew from 18 entries to ~65**, not guessed up front — every new one was added because
a real `Icon(Icons.*)` call site in this pass needed a Phosphor equivalent and none of the
original 18 domain-specific names fit. Verified against the real `phosphor_flutter` package source
(`phosphor_icons_base.dart`'s 1,512 static methods) before use, not assumed — three names
(`selfHeal`→`bandaids`, `history`→`clockCounterClockwise`, the three library-zoom
`density{Small,Medium,Large}` steps) needed a second lookup pass when the first guess didn't
exist. The zoom control specifically needed *visually distinct* icons (dots→squares→one square)
since the icon itself is the size cue in a `SegmentedButton` with `showSelectedIcon: false` — a
single reused glyph there would have defeated the control's whole point.

**Two real widget-library bugs found and fixed while doing this, not feature-code bugs:**
`ui/layout.dart`'s `KeyValueList` wrapped its label in a bare `Text` inside a `mainAxisSize: min`
`Row` — fine for the original hand-picked `labelWidth`s, but the row's *usable* width is
`labelWidth` minus the row's own right padding, so a label like "Last run" that fit the original
76px gutter no longer fit the ~68px left after the padding subtraction, throwing a real
`RenderFlex` overflow (caught by `live_layout_test.dart`, not `flutter analyze` — D19's
precedent again). Fixed generically in the shared widget (wrapped in `Flexible` + `maxLines: 1` +
ellipsis, matching `AppText`'s own default-safe philosophy) rather than hand-tuning
`run_summary.dart`'s `labelWidth`, since any future `KeyValueList` consumer would hit the same
class of bug with a long enough label. `core/dependency_models.dart`'s `DependencyLevel.icon`
getter (Material `IconData`) couldn't become `AppIcons`-based directly — `ui/` sits between
`core/` and `features/` (D100's own layering rule), so `core/` importing `ui/icons.dart` would
invert it. Fixed the same way D100 handled `ServiceState.statusKind`: a small feature-level bridge
extension (`_DependencyLevelIconX`, duplicated once in `dependencies_tab.dart` and once in
`overview/dependency_strip.dart`, its only two consumers) rather than relaxing the layering rule.
`core/funnel_stage.dart`, `core/agent_image.dart`, and `core/library_image.dart` hit the identical
constraint and were retokened (spacing, colors) but deliberately **not** converted to `AppIcon`/
`NumericText` for the same reason — flagged in each file with a comment rather than silently left
inconsistent.

**Eleven `.when()` sites named in AUDIT §6 — nine converted to `stateView`, two confirmed
correctly left alone.** `library_rail.dart` (×2), `log_console.dart`, `notification_center.dart`,
`devices_tab.dart`, `ops_tab.dart`, `queue_tab.dart`, `entity_yield_dialog.dart` now use
`AsyncValue.stateView()` with real `LoadingView`/`ErrorView`/`EmptyView` states and retry
callbacks (several gained a working retry button they didn't have before, e.g. `queue_tab.dart`,
`ops_tab.dart`'s spec list). `core/agent_image.dart` and `core/library_image.dart` were confirmed,
not just skipped — AUDIT §6 already called these "correctly bespoke — leave" (per-image inline
placeholders, not page-level states), and building through them confirmed that judgment still
holds. `live/device_bar.dart`'s `.when()` also stays hand-rolled by design (AUDIT §6: "acceptable,
it's a header strip") — only tokenized, not restructured, since a full `ErrorView` would be far
too heavy for a compact header control.

**`test/token_coverage_test.dart` written**, encoding PLAN_V2.md's three "must return nothing"
greps as real `flutter test` assertions (`Color(0x` outside `core/theme/`, named `Colors.*`
outside `core/theme/` except `Colors.transparent`, `fontFamily: '` outside `core/theme/`) plus the
one exception the plan's own criteria comment names by hand: the QR quiet zone
(`themes/classic.dart`'s `qrQuietZone: Colors.white`, where `AppTokens.chart.qrQuietZone` is
*defined*) is excepted the same way `core/theme/` itself is for the other two patterns. Reading
`lib/` from disk at test time (`dart:io`, matching every other test's `Directory.current`-relative
convention) rather than shelling out to `grep`, so this suite runs anywhere `flutter test` does,
Windows included, with no external tool dependency. One genuine false-positive found writing it:
`ui/status.dart`'s own doc comment for `OutcomeBadge` quoted the two hex literals it used to
replace — literally matching the `Color(0x` pattern from inside a comment. Fixed by rewording the
(now-stale, since D101 already did the retarget) comment rather than teaching the test to skip
comments, since a genuine hardcoded color hiding behind a comment-like string is exactly the kind
of near-miss this test exists to catch.

**Verified:** `flutter analyze` clean across all of `lib/` and `test/`. `flutter test` 121/121
(118 prior + 3 new in `token_coverage_test.dart`) — one real round of test breakage from the
migration itself, all in icon/text finders that were asserting against the exact Material
`IconData`/string this session replaced, fixed by updating the finders to the new Phosphor
glyph + weight rather than the app code (`flows_layout_test.dart`'s info-tooltip icon,
`notification_center_layout_test.dart`'s bell/filter/open-external icons ×3,
`ops_tab.dart`'s empty-state string losing its trailing period in translation to `EmptyView`).
`flutter build windows --debug` succeeds. Built and started for you per rule 5 — not clicked
through by Claude. **Deliberately out of scope, left as-is:** every `AlertDialog`-based confirm
dialog (`force_run.dart`, `library_toolbar.dart`'s apply/delete, `limit_card.dart`'s revoke-style
confirms, etc.) — `AppDialog` exists in `ui/overlays.dart` but PLAN_V2.md's V2.3 checklist doesn't
name a dialog-shell migration as one of its bullets, and rewriting a confirm dialog's structure
sight-unseen (rule 5: the user drives the app, this session cannot) carries real risk for a widget
whose whole job is a correct Cancel/confirm button pair. `AppTable` was not substituted for the
Ranking tab's hand-built D77 table, nor was `ResizableSplit` substituted for any of the thirteen
AUDIT §11 hardcoded-width splits — both are explicitly named as V2.11/V2.9's own scope in
PLAN_V2.md's sequencing notes, not V2.3's.

---

## 2026-08-05 — V2.3 migration started, split into two halves (D101 · part 1 of 2)

### D101 · The `AppPalette` shim deleted; every hardcoded color found by AUDIT §2 now reads a token

**Chosen scope for this half:** PLAN_V2.md's V2.3 is explicitly flagged as the plan's largest
single checkpoint, with its own sanctioned split ("split it by feature directory... each half
is independently verifiable"). Rather than a shallow first pass across all ~90 files, this half
does one thing completely: closes every real color-token gap AUDIT §2 named, verified against
the acceptance grep. The rest of V2.3 — wrapping all seven screens in `AppPage`, the `EdgeInsets`
sweep, `NumericText`/`AppIcon`/`Gap` conversion, the eleven remaining `.when()` sites, and
`test/token_coverage_test.dart` — is unstarted and is part 2.

**`core/app_theme.dart` (the `AppPalette`/`TerminalPalette` deprecated shim, kept for exactly
one checkpoint per V2.1's own comment) is deleted.** Its five remaining call sites
(`flow_card.dart`, `title_bar.dart`, `service_terminal.dart` ×5, `dependency_models.dart`,
`service_models.dart`) now read `theme.tokens.status.*`/`theme.tokens.terminal` directly.

**All thirteen hardcoded colors AUDIT §2 catalogued by file:line are gone**, each mapped to the
token the audit table already named: `log_console.dart`'s `Colors.amber.shade700` →
`tokens.status.warn.fg`; `service_detail.dart`'s three duplicate hex literals (`0xFFFFB454` /
`0xFF3DD68C` ×2 — the audit's "sharpest example," typed by hand from `AppPalette.dark`'s own
values) → `tokens.status.warn/good.fg`; `notification_center.dart`'s four `Colors.*Accent`
level colors → a `_levelColor(tokens, level)` function replacing a `static const` map (which
can't reach `theme` — the const-context constraint is why this one was a map literal instead of
a switch in the first place); `devices_tab.dart`'s two `Colors.white` QR-background instances →
`tokens.chart.qrQuietZone` (the token DESIGN_SYSTEM §1.4 built for exactly this — first real
consumer) and its `Colors.green` → `tokens.status.good.fg`; `ops_tab.dart`'s `Colors.green` →
same.

**`OutcomeBadge`/`BadgeTone` retargeted onto `ui/status.dart`'s V2.2-built version, not just
retokened in place** — `features/live/surfaces/surface_common.dart`'s local `OutcomeBadge`
class and `BadgeTone` enum are deleted outright; its five call sites
(`follow_surface.dart`, `ingest_surface.dart` ×2, `classify_surface.dart`,
`scrape_surface.dart` ×2) now import `ui/status.dart` and pass `StatusKind` (`good`/`bad`/
`neutral` map 1:1, no behavior change). `toneFor(verdict)` stays in `surface_common.dart` —
domain logic (what `'PRIVATE'` means) has no business living in `ui/`, only its return type
changed. This is COMPONENTS.md §3's plan for this widget, done as part of the migration rather
than left stranded as an unused duplicate.

**Verified:** `grep -rn "Color(0x" app/lib --include=*.dart | grep -v core/theme/` and
`grep -rn "Colors\.[a-z]" app/lib --include=*.dart | grep -v Colors.transparent` both return
nothing outside `core/theme/` (where token values are legitimately defined) — the first two of
V2.3's three acceptance greps already pass, ahead of `token_coverage_test.dart` existing to
enforce it. `flutter analyze` clean, `flutter test` 118/118 unchanged, `flutter build windows
--debug` succeeds. Built and started for you.

---

## 2026-08-04 (continued) — V2.2 component library implemented

### D100 · `app/lib/ui/` built against the tokens; only two pre-existing widgets actually moved

**Built:** all twelve files COMPONENTS.md specifies — `surfaces.dart` (`AppPanel`/`AppCard`/
`AppWell`/`AppOverlay`), `text.dart` (`AppText`/`MonoText`/`NumericText`/`AnimatedCounter`),
`status.dart` (`StatusKind`/`StatusDot`/`StatusChip`/`CountBadge`/`OutcomeBadge`),
`buttons.dart` (`AppButton`/`IconAction`/`ButtonGroup`), `page.dart` (`AppPage`/`PageHeader`/
`SectionHeader`/`Toolbar`), `fields.dart` (`AppTextField`/`SearchField`/`AppSelect`/
`AppSwitch`), `layout.dart` (`ResizableSplit`/`Gap`/`AppDivider`/`MetricRow`/`KeyValueList`),
`feedback.dart`, `overlays.dart` (`AppDialog`/`AppTooltip`/`AppMenu`/`AppSnack`), `data.dart`
(`AppTable`/`AppTableColumn`/`Sparkline`), `motion.dart` (`FadeSlideIn`/`AnimatedReveal`/
`PageTransition`, on `flutter_animate`), `icons.dart` (`AppIcon`/`AppIcons`, on
`phosphor_flutter`). `ui/command/` (the command palette) is explicitly out — that's V2.12's
scope per PLAN_V2.md, not this checkpoint's directory listing in COMPONENTS.md §0.

**Only `StatusDot` and the async-state trio actually moved, per PLAN_V2's own bullet list —
`OutcomeBadge`'s real call sites stay untouched.** COMPONENTS.md §3 says `OutcomeBadge` "keeps
its name and call sites — only its `BadgeTone` enum and hardcoded colors are replaced," which
reads like a V2.2 migration, but PLAN_V2.md's actual V2.2 checklist only names two moves:
`core/async_state_view.dart` → `ui/feedback.dart` and `features/services/status_dot.dart` →
`ui/status.dart`. Built `ui/status.dart`'s `OutcomeBadge`/`StatusKind` as the *target* shape,
left `features/live/surfaces/surface_common.dart`'s original `OutcomeBadge`/`BadgeTone`
completely untouched — V2.3's 90-file migration is what actually redirects the five surface
files. This matches the checkpoint's stated goal ("used by nothing yet") for every genuinely
new component, while still doing the two real moves the plan calls out by name.

**`StatusDot` generalised from `ServiceState` to `StatusKind` + an explicit `pulsing` bool** —
its transient-state pulse (AUDIT's "do not undo" list) is unchanged, just no longer tied to one
domain model. The two real call sites (`service_tile.dart`, `service_detail.dart`) needed a
small bridge, added as `features/services/service_status_kind.dart` (`ServiceState.statusKind`)
rather than teaching `core/service_models.dart` about `ui/status.dart`'s `StatusKind` — `ui/`
sits between `core/` and `features/` per COMPONENTS.md §0's own directory note, so `core/`
importing `ui/` would invert that layering. A feature-level bridge file was the correct home.

**`AppTokensX.tokens` needed the same fallback `AppPalette` already had, discovered by the
`ui/` tests themselves.** The dozen `theme.tokens.type.mono` reads V2.1 added compile fine
everywhere, but calling `.tokens` from a genuinely bare `ThemeData()` (no `AppTokens`
registered) still null-checks. Already fixed in V2.1 (`AppTokensX.tokens` falls back to
`buildClassicTokens()`) — V2.2 is what actually exercised that path for the first time, via its
own test harness (`test/ui/test_harness.dart`) which — unlike the ten pre-existing layout
tests — renders through the real `buildTheme(buildClassicTokens())` rather than a bare
`ThemeData()`, since these are exactly the widgets that read `theme.tokens`.

**One real test-authoring bug, not a component bug, caught by the tests themselves:**
`find.byType(MouseRegion).first` intermittently resolved to an unrelated ancestor `MouseRegion`
inserted by the Material/Overlay chain rather than `ResizableSplit`'s own drag handle — its
computed drag offset landed inside the *second* pane instead of on the handle, failing three
tests with a bad hit-test warning. Fixed by giving the handle's `GestureDetector` a real
`ValueKey('resizable_split_handle:$persistKey')` and asserting against the rendered pane's
actual `Size` (`tester.getSize`) rather than scanning every `SizedBox` in the tree by width
heuristics, which was fragile for the same underlying reason.

**Verified:** `flutter analyze` clean, `flutter test` **118/118** (52 prior, unchanged — the
two "moves" needed zero test edits since no test directly imported either old file — + 66 new
in `test/ui/`, including the two real-assertion cases PLAN_V2.md names: `ResizableSplit`'s
minimum-clamp/persistence/keyboard-nudge behaviour, and `AppTable`'s exact D77 invariant — one
`width: null` column absorbs all leftover width, fixed columns never grow). `flutter build
windows --debug` succeeds. Built and started for you — this checkpoint's test is a code review
per PLAN_V2.md ("nothing user-visible changed... skim `ui/` and say whether the vocabulary
matches how you think about the app"), not a click-through.

---

## 2026-08-04 (continued) — V2.1 token foundation implemented

### D99 · Token layer built; the mono-font swap is the one intentional visible change

**Built:** `app/lib/core/theme/` — `tokens.dart` (`AppTokens` plus every sub-token class from
DESIGN_SYSTEM.md §1: `SurfaceTokens`, `ContentTokens`, `AccentTokens`, `StatusTokens`,
`TypographyTokens`, `GeometryTokens`, `EffectTokens`, `SpacingTokens`, `MotionTokens`,
`ChartTokens`, plus `TerminalPalette` moved in from `app_theme.dart`), `density.dart`,
`build_theme.dart` (all ~40 `ThemeData` component sub-themes), `registry.dart`, and
`themes/classic.dart`. `flutter_animate` and `phosphor_flutter` added; `InterVariable(-Italic).ttf`
and `JetBrainsMono-{Regular,Medium,Bold}.ttf` downloaded from each project's GitHub release
(rsms/inter's `docs/font-files/` path 404s for the italic — pulled from the `Inter-4.1.zip`
release asset instead) and committed under `app/assets/fonts/` with both `OFL.txt` licenses.

**Classic's exact-match mechanism:** `themes/classic.dart` calls
`ColorScheme.fromSeed(seedColor: 0xFF6C63FF, brightness: dark)` — the same call `app.dart` used to
make directly — and reads `SurfaceTokens`/`ContentTokens`/`AccentTokens` straight off the
generated scheme's fields (THEMES.md §1's table), rather than hand-transcribing hex values. Every
one of `build_theme.dart`'s ~40 sub-themes is then set explicitly from those tokens (never left to
fall back on `ColorScheme`-driven Material defaults), so the checkpoint's "no visible change"
claim rests on the explicit values matching Material 3's own default derivation for that seed,
not on the base `ColorScheme` alone.

**The one deliberate exception to "nothing else changes yet":** DESIGN_SYSTEM.md §1.5 says the
`'Consolas'`/`'monospace'` mix (AUDIT §7, 12 call sites across 8 files) becomes `tokens.type.mono`
explicitly, and PLAN_V2.md's own checkpoint test names this as the one expected visible diff. Did
exactly those 12 call sites — no other literal at those sites touched, no other file migrated.

**`AppTokensX.tokens` needs a fallback, same as `AppPalette` did.** The ~12 mono call sites now
read `theme.tokens.type.mono` unconditionally, but the ten existing layout tests build their own
bare `ThemeData(useMaterial3: true, brightness: dark)` with no `AppTokens` registered (same
pattern D19/CP 7.3 already established for `AppPalette`) — a force-unwrapped `extension<AppTokens>()!`
crashed four of them (`services_layout_test.dart`) with a null-check error. Fixed the same way
`AppPalette.dark` was: `AppTokensX.tokens` falls back to `buildClassicTokens()` when nothing is
registered. This makes `tokens.dart` → `themes/classic.dart` → `tokens.dart` a real cyclic import;
confirmed Dart accepts library-level import cycles (unlike `part`/`part of`) — `flutter analyze`
stays clean and all 52 tests pass with it in place.

**`AppPalette` kept as a real deprecated shim, not just co-existing.** `TerminalPalette` moved out
of `app_theme.dart` into `tokens.dart` (its constructor requires one for `AppTokens.terminal`);
`AppPalette`'s `.palette` getter now builds the legacy shape on demand from whichever `AppTokens`
is registered (`tokens.status.good.fg` etc.), falling back to the old hardcoded `AppPalette.dark`
only when no `AppTokens` extension exists at all — so the five call sites still reading
`theme.palette.*` (`flow_card.dart`, `title_bar.dart`, `service_terminal.dart`,
`dependency_models.dart`, `service_models.dart`) needed zero changes and will keep working
unchanged until V2.3 migrates them.

**Not specified by THEMES.md's Classic table, so derived rather than guessed:** `borderSubtle`
(`outlineVariant @ 0.5`), status `good`/`info`/`warn` containers (existing fg values, alpha-blended
onto `surfaceContainer` for the container, fg reused as `onContainer` — `bad` uses the seed
scheme's own `errorContainer`/`onErrorContainer` instead, since that's a real generated value, not
a guess), `bodyHeight`/tracking/`chart.*` (Classic's row in THEMES.md §1 doesn't give these — nothing
in the app reads `AppTokens.chart` or applies letter-spacing yet, so precision here doesn't affect
the pixel-identical checkpoint). Flagged here rather than presented as spec.

**Also not literally achievable, and not attempted:** `DESIGN_SYSTEM.md` §2's nine-role type scale
(pageTitle 22, cardTitle 15, etc.) does not match Material 3's own default `TextTheme` sizes
(headlineSmall 24 not 22, titleMedium 16 not 15, …), so setting it changes `ThemeData.textTheme`'s
baked-in sizes for Classic too. This is expected to be near-invisible today because the audit's
own evidence is that most on-screen text already comes from inline `TextStyle` overrides at the
~90 feature-file call sites rather than `theme.textTheme.*` — but it is not verified pixel-by-pixel,
and is exactly the kind of thing the checkpoint test is designed to catch.

**Verified:** `flutter analyze` clean, `flutter test` 52/52 (unchanged — no test file edited),
`flutter build windows --debug` succeeds. The Windows ephemeral `cpp_client_wrapper/` was
regenerated (stale/incomplete, unrelated to this checkpoint) and a stale `ia_control_center.exe`
from an earlier session had to be closed (confirmed with the user first) before the linker could
write the new binary. Built and started for you per rule 5 — not clicked through by Claude.

**Your live check caught one real bug, same session:** the Live screen's flow-selector
`ChoiceChip` (`live_page.dart:98`) was dark-on-dark when selected — `chipTheme.secondaryLabelStyle`
(the label style `ChoiceChip` uses while selected) was set to `accent.onPrimary`, which is meant
for text on a *solid* `accent.primary` fill, but the selected chip's actual background is
`accent.muted` — a translucent tint, still close to the dark page color, not a solid fill. Fixed
to `accent.primary` (the light lavender), matching `checkmarkColor`, which already used the right
token. Nothing else in `build_theme.dart` pairs `onPrimary` with a non-solid background the same
way (checked `filledButtonTheme`/`badgeTheme`, both solid-fill, both correct;
`segmentedButtonTheme`/nav rail's selected state already used `accent.primary` correctly). Rebuilt,
re-analyzed, re-tested (52/52), restarted for you.

---

## 2026-08-04 (continued) — v2's two open design forks answered

### D98 · Library double-click opens a lightbox; Classic stays the launch default

**Asked:** the two questions `docs/v2/VISUAL_INPUTS.md` left open after the observation pass
(D97) — both changes to existing behaviour, so both flagged for the user rather than assumed.

**Chosen, on the user's answer:**

**Double-click in the Library grid opens a lightbox.** The user confirmed they don't use
double-click at all, which makes this free: `library_tile.dart:84`'s copy-id moves to the
right-click menu — where it already exists (`library_tile.dart:58`), so no capability is lost —
and double-click instead opens the large single-image view review mode uses. This is the browsing
answer to the problem D97 measured: a 1080×2246 profile page is unjudgeable at ~120px.
**Explicitly untouched:** plain click toggles, Space toggles, arrows move focus only, Shift
ranges — D48 / `feedback-multiselect-toggle`, a recorded user preference.

**Classic stays the default theme on first launch.** v2.0.0 opens looking exactly as the app does
today; the other five themes are one click away in the new Appearance tab. Rejected making
Command Deck the default despite it being the theme designed for how this app is actually used —
an overhaul that changes everything the moment it launches gives the user no reference point, and
the welcome dialog pointing at the Appearance tab is a better introduction than a surprise.

**Cost:** none. Both were scoped into existing checkpoints (V2.10 and V2.4 respectively) rather
than adding work. With these closed, **no open question blocks v2 implementation.**

---

## 2026-08-04 (continued) — v2 planning corrected by actually looking at the app

### D97 · Rule 5 lifted for one session; three planning errors found by observation

**Asked:** the user explicitly lifted rule 5 ("the user drives the app, never you") for this
session — "lets ignore the rule that you cant see the app or screen … ask for it once do the job" —
so the v2 plan could be checked against the real thing rather than inferred from source. Rule 5
remains in force by default; this was a scoped, one-session exception.

**Method:** `flutter clean` → dart-MCP `launch_app` on device `windows` (debug) → Win32
`SetCursorPos`/`mouse_event` clicks at logical client coordinates → `Graphics.CopyFromScreen` per
screen. `flutter_driver` was unavailable (the app never calls `enableFlutterDriverExtension()`),
and `launch_app` returns the `flutter run` host pid rather than the window-owning child
`ia_control_center.exe` — both noted in `docs/v2/OBSERVED.md` for repeatability. Only navigation
was clicked; no switch, trigger, apply, delete or ops job was touched. Nine screenshots committed
under `docs/v2/screens/`.

**Three errors found, all now corrected in the v2 docs:**

**1. The window is landscape, not tall and narrow.** Measured 2560 × 1600 at 150% scaling, mirror
taking 443 logical px, giving the app **1253 × 1013 logical** (content ≈ 1168 × 973) — about
1.24 : 1. D95 had inferred "~1250 × 1400, taller than wide" from `main.dart`'s geometry math
without accounting for the work area's real height at 150%. **Consequence:** Flows' vertical
pipeline *stands*, but on different reasoning (the screen wastes ~55% of its height, and at 1168px
wide each node becomes a horizontal strip holding everything in one row); Live's vertical split is
**reversed** — at 973px of content height a vertical split gives each pane ~470px, too short for
both a log console and portrait cards. Live keeps a horizontal split, made resizable.

**2. The Library grid uses one cell aspect ratio for two very different image shapes** — invisible
from source, and arguably the worst visual defect in the app. Cells are near-square; `entities`/
`scraped`/`follow_queued` hold 1 : 2.08 portraits (~40% of each cell wasted, letterboxed
left/right) while `scanned`/`gender_valid`/`gender_invalid`/`scrape_queued` hold 5.45 : 1 row crops
(**~82% wasted**, letterboxed top/bottom). In the row-crop folder only 9 cells fit the grid pane
where a matched shape holds ~40 — a 4× throughput difference on a 6,635-image backlog. D41's
`BoxFit.contain` choice is right and stays; the container just has to match the content. Now the
top Library fix, ahead of review mode.

**3. The dominant problem is horizontal emptiness, not density.** Flows leaves ~55% of the screen
black; Settings' switch rows have ~1100 logical px between label and control; Library spends 38% of
its width on two navigation rails; Live's fixed 420px visualization column was ~95% empty. The
original audit read the app as cluttered — it is the opposite.

**Two further findings worth recording.** Four of the five Flow cards render an *identical* amber
hourglass above the *identical* words "Waiting on condition", so the screen whose purpose is
showing what the pipeline is doing communicates almost nothing without hovering each ⓘ in turn —
worse than the source-only audit predicted. And Services' detail pane turned out to already be the
app's best design (an uppercase-micro-label metric strip, self-explaining switch cards, a framed
terminal with search/copy); it is promoted to a shared `MetricStrip` component rather than a new
treatment being invented.

**One open question closed by observation:** the light-theme terminal palette is safe — real `adb`
output is essentially monochrome, with no dark-on-dark ANSI. The "always dark" override stays as a
preference, not a fallback.

**Cost:** none to the plan's shape — thirteen checkpoints stand, and the scope boundary (everything
inside `app/`, no agent changes) is unaffected. Adding a `driver_main.dart` entrypoint with
`enableFlutterDriverExtension()` would make any future observation pass far more precise than
coordinate clicking, and is worth doing if this recurs.

---

## 2026-08-04 (continued) — v2.0.0 UI/UX overhaul: planned, not yet built

### D94 · Own token layer on Material 3, not a component framework

**Asked:** the user opened a session whose stated goal is a "MAJOR OVERHAUL" of the control
center's UI/UX — the app works correctly everywhere, but looks generic, and they want real themes
that change its character completely. Planned under Opus, to be implemented under Sonnet from the
docs produced. Everything below is **planning only** — no `app/` code changed this session.

**The diagnosis, from reading all 90 files under `app/lib/`:** the entire theme is four lines
(`app.dart:15-21`) — `useMaterial3`, `brightness: dark`, one `colorSchemeSeed`, one transparent
background. **None** of `ThemeData`'s ~40 component sub-themes are set, and there is no `textTheme`
customization at all. So every card, button, chip, field, tab, tooltip and dialog renders at
Material's default. The app doesn't look generic because it uses Material — it looks generic
because it uses Material's *defaults*. `core/app_theme.dart` (the CP 7.3 centralization) holds
only three status colors and a terminal palette; 13 hardcoded colors survive outside it, three of
which (`service_detail.dart:305/314/380`) are the exact same hex values as `AppPalette`'s,
re-typed by hand.

**Chosen:** build an `AppTokens` `ThemeExtension` covering surface/content/accent/status/type/
geometry/effects/space/motion/chart/terminal, and a `build_theme.dart` that fills every one of
those ~40 sub-themes from it. Six themes ship: Classic (today's look, preserved, derived from the
real seed rather than transcribed), Command Deck, Nocturne, Mica, Daylight, Swiss.

**Rejected: adopting `shadcn_ui` (0.56.0), `forui` (0.25.0) or `fluent_ui`.** All three are good.
All three would mean rewriting 90 files against a new widget vocabulary — and those files encode
roughly a dozen hard-won overflow and constraint fixes (D19, D43–D46, D77, D87, D89, D93) that a
rewrite would have to rediscover live, on a single-screen laptop, against a real pipeline. Both
shadcn_ui and forui are also pre-1.0 and moving fast. `fluent_ui` would serve exactly one of the
six themes well and fight the other five.

**Why the token layer wins:** a `Card` with a themed shape, border, elevation strategy and surface
color is not recognisably a Material `Card`. The widget tree barely changes; the theme does all the
work. It also makes a seventh theme one file plus one registry line, which is the real test of
whether the abstraction holds.

**Cost:** V2.3 is a 90-file mechanical migration with real regression potential. Mitigated by the
ten existing layout tests (D19's precedent — overflow is a paint-time error `flutter analyze`
cannot see) plus a `token_coverage_test.dart` enforcing that `grep -rn "Color(0x" app/lib` returns
nothing outside `core/theme/`.

### D95 · Flows renders as a vertical pipeline; Live splits vertically

**Asked:** which screens are shaped wrongly, not merely styled plainly.

**Chosen:** three re-architectures. **Flows** becomes a node/edge pipeline with the inter-stage
backlog counts on the edges — `entity_ingest → scan → classify → scrape → follow` is a strict
pipeline whose entire gating logic (D86's `SCRAPE_RESERVE_FACTOR`, D91's `SCAN_RESERVE_TARGET`) is
about the size of those queues, and the current five-cards-in-a-`Wrap` shows none of them; they
live on a different tab, in the Library folder rail. The two human-in-the-loop edges get marked and
made clickable, which is the first time the app has ever shown that the pipeline *waits on the
user* at two specific points. **Overview** becomes a bento grid with a computed hero status
sentence, replacing a page that embeds five full 360px `FlowCard`s and therefore duplicates the
Flows screen rather than summarising it. **Library** gets a keyboard-driven fullscreen review mode,
because the current grid renders a 1080×2246 profile page into a ~120px thumbnail — you cannot
actually read what you are judging.

**Both new layouts are vertical, deliberately.** `main.dart` sizes the window to fill the space
right of the scrcpy mirror — roughly 1250×1400 logical px, taller than it is wide. A horizontal
five-stage diagram would either wrap awkwardly or shrink each node past usefulness; the Live
screen's current fixed 420px visualization column is already flagged *in its own source comments*
as tuned to `entity-scrape` only, with a warning that follow/classify will need different values.

**Flagged as a bet, not a certainty:** I have never seen the app render (rule 5), so the aspect
ratio is inferred from arithmetic in `main.dart`, not observed. `docs/v2/VISUAL_INPUTS.md` asks for
one screenshot that confirms or kills all three vertical decisions before V2.5 begins.

> **⚠️ Amended same day by D97 — the bet was half wrong.** The window is landscape
> (1253 × 1013 logical), not tall and narrow. Flows' vertical pipeline survives on better
> reasoning; Live's vertical split is reversed. See D97.

### D96 · Design-language triage — three styles argued against, not deferred

**Asked:** the user supplied sixteen design inspirations (Minimalist, Glassmorphism, Neumorphism,
Brutalism, Bento, Skeuomorphism, Neo-brutalism, Claymorphism, Cyberpunk, Y2K, Dark Academia,
Swiss/International, Editorial, Luxury, Retro-futurism) and asked for a few that match the app,
with the rest kept as a backlog.

**Chosen for v2.0.0:** **Swiss/International** — the one classical design language that is
actually *about dense information* (timetables, wayfinding, technical tables), which is all this
app renders. **Bento** adopted as a *layout pattern* for Overview rather than a theme, since it's a
composition idea with no color or type language of its own — that way it works in all six themes
instead of one. **Glassmorphism** judged already served by Mica: real OS-composited Mica rather
than stacked `BackdropFilter`s, same aesthetic at a fraction of the GPU cost, and native to the
platform. **Minimalist** already served twice over, by Command Deck and Swiss from opposite
directions.

**Backlogged with real sketches:** Cyberpunk, Editorial, Dark Academia, Retro-futurism (v2.1 —
good fit, low-to-medium cost); Neo-brutalism, Luxury, Y2K (v2.2 — prototype first).

**Argued against outright, rather than merely deferred:** **Neumorphism** and **Claymorphism** —
the aesthetic *is* low contrast, since soft embossing depends on foreground and background being
nearly the same value. They fail the 4.5:1 floor by construction, not by execution, and cannot be
made accessible while remaining recognisable. For a monitoring tool whose status colors must be
unmissable, that is disqualifying. **Skeuomorphism** — needs bespoke raster assets per component;
an art-production project, not a theming one, and it doesn't scale to 40 sub-themes.
**Brutalism proper** (as distinct from neo-brutalism) — deliberately hostile ergonomics, directly
opposed to rule 7.

**Cost:** none yet. Adding any backlogged theme after V2.4 is one file plus one registry line.

---

## 2026-08-04 (continued) — message-triggered ingest left a stale gate on the Flows card

### D92 · Wake the ingest poll loop right after a message-triggered run, instead of leaving a stale gate

**Asked:** while checkpoint-testing D91 live (posting an entity URL to the Telegram channel to
verify the new scan gate), the user noticed the Ingest card stayed on "Checking…" for a few
minutes after its run had already completed (confirmed by "Last run: COMPLETED · 35s" showing
correctly at the bottom of the same card) — not a functional problem, just a confusing few minutes
of stale status.

**Root cause: two independent triggers write the same shared state, and only one of them leaves it
accurate.** `entity_ingest_time_trigger()` (the periodic poll, `INGEST_POLL_WAIT` = 10 min default)
always recomputes an accurate gate — `no_work` if nothing's queued, or a real one before it runs.
`entity_ingest_message_trigger()` (Telethon's own `NewMessage` event, fires instantly on a channel
post, D66) sets `gate={ok:true, reason:"message"}` before running, then on completion only calls
`self._set_state("entity-ingest", phase="idle")` — `_set_state` only updates the keys passed
(`state.update(fields)`), so the "message" gate from the run itself is left sitting there
untouched. `flow_card.dart`'s `_kindOf` doesn't match `running`/`day_paused`/`cooldown` for that
combination and falls through to the generic default, `_StatusKind.polling` → "Checking…" — an
accurate read of a stale state, not a UI bug. Nothing corrects it until the **separate**,
independently-timed poll loop happens to reach its own next iteration — anywhere from seconds to
the full 10 minutes later, unrelated to when the message actually arrived.

**Fixed by waking the existing poll loop instead of duplicating its gate logic.** Right after the
message-triggered run finishes, `entity_ingest_message_trigger()` now queues `skip_wait` for
entity-ingest (`self._commands.setdefault("entity-ingest", []).append("skip_wait")`) — the exact
same command "Trigger now" and the REST command endpoint already use, consumed by the existing,
already-tested `wait_until()` machinery. If the poll loop is mid-wait, it wakes immediately,
re-checks `entities_exist`, and sets a real gate right away instead of leaving the stale one there.
Chosen over teaching the message handler to compute its own resting gate, since that would
duplicate logic the poll loop already owns and could drift out of sync with it over time.

**Verified:** a throwaway script building a real `Prefect` instance via `__new__` (skips `__init__`,
so no Postgres/Telegram/device construction needed) with `Config.get` monkeypatched to short
durations, exercising the real `wait_until()`/`_set_state()`/`_commands` machinery directly — 3/3:
`skip_wait` is queued after the simulated message-triggered run, a concurrently-waiting
`wait_until` wakes on it almost immediately (0.06s, not the full 5s), and — proving the first result
isn't a fluke of a short tick — the same wait genuinely runs the full ~5s when nothing is queued.
Import sanity-check clean. Deployed for real: pushed to `Insta-Automate`'s `feat/control-center`
(`9ad212c`), `ia build`, `kubectl rollout restart deployment/insta-automate`. The rollout took
longer than usual (~3.5 min on `insta-automate-flow-init`, the container that re-registers all six
Prefect deployments) and the old pod logged one transient `ConnectionError: Connection to Telegram
failed 5 time(s)` restart while being torn down mid-shutdown — both are normal rolling-restart
churn on the outgoing pod, unrelated to this change; the new pod came up clean and stayed at 0
restarts. Confirmed via `kubectl exec` that the running pod's loaded `Prefect.serve` source
contains the `skip_wait` queuing (D39's precedent). Worker pod untouched (trigger-loop-only
change, same reasoning as D84/D91). **You tested live afterward and confirmed it works** — the
Ingest card now settles to its real resting state promptly instead of sitting on "Checking…" for
minutes. Committed.

---

## 2026-08-04 (continued) — Flows cards decluttered: mechanism/gate text moved behind an info tooltip

### D93 · Always-visible mechanism sentence + raw gate formula replaced with a small info icon + tooltip

**Asked:** the user flagged the Flows screen as "kind of ugly" with "all this extra text" — every
card always rendered two stacked technical text blocks below the status line: D84's plain-language
mechanism sentence, and (when blocked) the gate's raw condition string verbatim from the pipeline
(e.g. `scanned+gender_invalid+gender_valid+scrape_queued = 6581 ≥ SCAN_RESERVE_TARGET = 1000 (every
queued e...)`), truncated mid-formula on longer flows. Both were always on, competing with the
status/counters/buttons for attention on every card regardless of whether the user needed that
detail right now.

**Chosen, after presenting three concrete options with mockups:** an ⓘ icon next to the status
subtitle, tooltip-only — the mechanism sentence and (when present) the gate detail move entirely
into the icon's `Tooltip.message` (joined with a blank line), off the card by default. The icon
tints to the theme's error color when the flow is genuinely blocked (`gate.detail/reason` present
and `!gate.ok`), giving an at-a-glance signal without spelling out the formula. **Rejected:** an
expandable "Details ⌄" disclosure (adds a click + card-height change just to read the same text)
and keeping the text inline but shortened (would require parsing/humanizing arbitrary pipeline
gate strings client-side, a real maintenance risk since those strings' shapes aren't a contract).

**A first pass over-cropped the fix.** The subtitle `Text` was wrapped in `Expanded`, which
stretches to fill the row before the icon — so on short subtitles ("Paused for the day", "Waiting
on condition") the icon landed pinned to the far right of the row, next to the switch, with a wide
dead gap between the text it explains and the icon itself. Caught by the user from a live
screenshot, not anticipated. Fixed by swapping `Expanded` → `Flexible`: the text now only claims
the width it needs (still ellipsizing correctly if it ever runs long, since `Flexible`'s default
`FlexFit.loose` still gets the same max-width constraint `Expanded` did), and the icon sits
immediately after it instead of at the row's far edge.

**Verified:** `flutter analyze` clean, `flutter test` 52/52 (two cases in `flows_layout_test.dart`
rewritten from asserting the mechanism text rendered inline to asserting it via
`find.byTooltip(...)`, since that's genuinely where it lives now — not just a cosmetic tweak to the
same assertion). `flutter build windows --debug` succeeds. Built and started for you twice (once
per round), not clicked through by Claude. **You confirmed both rounds live** — the first pass
read as much cleaner, the icon-placement bug was then caught and fixed the same session.

---

## 2026-08-04 (continued) — entity-scan gets its own curation-backlog reserve gate

### D91 · A new `SCAN_RESERVE_TARGET` gate on entity-scan, scoped to PROFILE+PUBLIC only

**Asked:** entity-scrape already pauses once `scraped+follow_queued` reaches a reserve target
(`SCRAPE_RESERVE_FACTOR`), keeping that pool bounded. The user wanted the identical idea one stage
earlier: entity-scan should pause once `scanned+gender_invalid+gender_valid+scrape_queued` — the
whole human-curation backlog between scan output and scrape input — reaches a cap, so `IA_DIR`
can't grow unbounded ahead of the two manual mobile-review steps. Unlike `SCRAPE_RESERVE_FACTOR`
(a multiplier on a daily limit), the requested cap is a flat number: 1000. And the gate is scoped
narrower than scrape's: only when the *next queued entity* is a `PROFILE` with `PUBLIC` access —
a `PRIVATE` profile can't be scanned for followers/following at all (nothing to gate), and a
REEL/POST's likers scan is a one-shot job, not an ongoing backlog contributor, so both always run
regardless of backlog size.

**Chosen — `SCAN_RESERVE_TARGET` (default 1000), mirroring `SCRAPE_RESERVE_FACTOR`'s existing
"reserve" vocabulary** rather than inventing new terminology, even though this one is a flat count
instead of a multiplier — the underlying concept (a bounded downstream pool between two flows) is
identical to what "reserve" already means everywhere else in this codebase (the Reduce-reserve
button, D86, uses the same word for the analogous scrape→follow pool). `force` (Trigger now)
bypasses the gate, same as every other flow's gate.

**First cut only checked `entities[0]` — wrong, caught before deploy mattered.** The initial
version read `subject = entities[0]` and blocked the whole trigger loop if that single entity was
gated. `Entity.entity_priority_order()` (unrelated to this gate, pre-existing) sorts by access
first (PRIVATE=0, PUBLIC=1) then type (PROFILE=0, REEL=1, POST=2) *within* the same access tier —
and ingest actually resolves real PUBLIC/PRIVATE access for REEL/POST entities too
(`device._reel_entity_access`/`_post_entity_access`), not just profiles. So a public REEL sorts
*behind* a public PROFILE in the same access tier, which means a single stuck public profile at
`entities[0]` would silently block every REEL/POST/private-profile entity queued behind it
forever — exactly backwards from "any other type of entity need not need to follow this and SCAN
should start normally." Found by re-reading `entity_priority_order()` while explaining the design
to the user, before they ran the live test that would have caught it (queue a blocked public
profile, then a reel, and watch the reel never scan).

**Fixed: `_scan_reserve_gate(entities, force) -> (subject, count, target)` walks the whole
priority-ordered queue** and returns the first entity the gate doesn't block — `None` only if
every queued entity is a gated, over-target public profile. The whole-library backlog count is
computed at most once (lazily, on first gated candidate), not per candidate, so a queue full of
non-public-profile entities never touches the filesystem at all. `entity_scan_trigger()` uses
`subject` directly; a `None` result sets the `backpressure` gate (reusing scrape's own gate-reason
name, scoped per-flow already so no collision) and skips the run entirely, matching the user's own
framing ("donot trigger automatic flow if not passed") — it never skips ahead past a *blocked*
entity to try a lower-priority one; it only skips past entities the gate never applied to in the
first place.

**Extracted into a standalone function, not inlined**, unlike scrape's own backpressure check —
specifically so it could be unit-verified in isolation (a throwaway script, monkeypatching the
module's own `SCANNED_DIR`/`GENDER_INVALID_DIR`/`GENDER_VALID_DIR`/`SCRAPE_QUEUE_DIR` globals against
a scratch tree) without standing up the full `Prefect` class's Postgres/Telegram/device
dependencies. Final version: 7/7 checks, including the exact scenario the bug was found from
(a blocked public profile ahead of a public REEL in priority order — the REEL is still picked), a
private entity found regardless of position, force bypassing a fully-blocked queue, and the
backlog count computed only once and only when actually needed.

**Wired into both control-center pieces that read `Config`'s schema generically**, no other UI code
needed: `agent/src/ia_agent/config/schema.py` gained one `ConfigKey` entry (same `TIMING` group as
`SCRAPE_RESERVE_FACTOR`, since Settings' Limits tab and `LimitCard` are both fully schema-driven —
confirmed by reading `limits_tab.dart`/`limit_card.dart` before assuming a new UI widget was needed).
`flow_card.dart`'s always-visible mechanism line (D84) for `entity-scan` gained a clause naming the
backlog cap, reading it live from `configControllerProvider` the same way `SCRAPE_RESERVE_FACTOR`
is read in `force_run.dart`. The mobile client (`ia_manager`) is untouched — D84 already scoped it
out of the mechanism-line work entirely (no config-reading plumbing there today), and this gate
needs no client-side plumbing beyond the blocked/cooldown split it already has.

**Verified:** the throwaway `_scan_reserve_gate` script (7/7, final version) plus a real import
sanity-check of both changed `Insta-Automate` modules. All 15 agent verification scripts green
(541 + the new schema key, no suite asserts an exact key count). `flutter analyze` clean,
`flutter test` 52/52 unchanged (the existing `entity-scan` layout test already renders the
longer mechanism line at its test width with no overflow, and the `?? 1000` fallback keeps the
config-less test fixtures rendering the coded default rather than crashing on a missing key) —
the queue-walk fix is entirely `Insta-Automate`-side, so nothing on the Flutter side needed a
second pass. Deployed for real, twice: the first cut was pushed
(`Insta-Automate feat/control-center` `8552e32`), built, and rolled out to the scheduler pod
before the `entities[0]` bug was caught; the fix (`4d22cbe`) was then pushed, rebuilt, and rolled
out the same way (`kubectl rollout restart deployment/insta-automate` — scheduler only, this gate
lives in the trigger loop, which only the scheduler pod runs; the worker pod executes flow bodies
via `git_clone`-per-run and was never in scope, same reasoning D84 used for its own scheduler-only
gate change), with the running pod's loaded `prefect._scan_reserve_gate` source confirmed via
`kubectl exec` to match the fixed commit, not the first one (D39's precedent). The agent itself
was restarted once (`taskkill /F /IM ia-agent.exe`, the launcher respawned it) to pick up the new
schema key — confirmed live via `GET /api/config/schema`, and all three supervised services
stayed `adopted` with uptime intact across it (D87's lesson, checked again rather than assumed).
**You tested this live afterward and confirmed it works**, exactly the scenario that caught the
`entities[0]` bug in the first place: with the real backlog over 6000 (well past the 1000 target),
a queued `PROFILE`+`PUBLIC` entity correctly did not trigger a scan (blocked, confirmed via the
Flows card's gate detail), and a `REEL` queued right after it — behind the blocked profile in
priority order — scanned normally. Committed.

---

## 2026-08-04 (continued) — Mobile Library apply/delete now dual-writes to the paired agent

### D90 · Closing the Reduce-reserve/Syncthing race: mobile's Apply/Delete mirror straight to the desktop's own `IA_DIR`, not just locally

**Asked:** a real live bug — applying a scrape batch on mobile (promoting 10 images into
`follow_queued`) and immediately pressing Reduce reserve on the same phone dropped the count to 177
instead of the expected 180. Root cause: mobile's Apply/Delete only ever write to the phone's own
local `IA_DIR` copy; the laptop (where `entity_follow`'s pool count and Reduce reserve's stop
condition actually read from) only sees that change once Syncthing has propagated it — a race with
no guaranteed timing, so a trigger fired right after Apply can read a stale or half-synced count.
You asked for a fix that's robust across corner cases with **zero risk of image data loss**, and
confirmed the phone's own instant local UI feedback must stay exactly as instant as today.

**Chosen — dual-write, local-first.** Mobile's local file moves/deletes are completely unchanged
(same instant UI). Additionally, when paired and the agent is reachable, the exact same explicit
file list is mirrored to the desktop's own `IA_DIR` directly over the existing pairing connection —
so the laptop's canonical counts are correct by the time Apply's spinner stops, with no dependency
on Syncthing's timing for this specific race. Unpaired or agent-unreachable: silently falls back to
today's Syncthing-only behavior, zero regression.

**A real correctness risk was found and designed around before writing any mobile code**: both
`FolderScreen` and `EntityImagesScreen` paginate — Apply only ever acts on the current page
(`_batch`), which can be a strict subset of one entity's images. The agent's existing
`POST /api/library/apply` (CP 5.2) is coarse-grained by design — `selected` is treated as the
*complete* keep-list for that entity's whole directory, trashing everything else present. Naively
routing a per-page Apply through it would have trashed that entity's *other, not-yet-reviewed*
pages the moment the first page was applied — a real data-loss bug, not just a timing nuisance, and
exactly the kind of corner case you asked to be covered.

**Fixed by adding one new, deliberately dumb endpoint instead of reusing `apply`.** New
`ops.move(moves: list[{from, to}])` (`agent/src/ia_agent/library/ops.py`) + `POST
/api/library/move` (`agent/src/ia_agent/api/library.py`) — moves exactly the named pairs and
nothing else in either directory, mirroring precisely what mobile already computes locally
(`File.rename(...)`). `/api/library/delete` (already explicit-path-based, CP 5.2) is reused as-is
for the "unselected → trash" half — no agent change needed there. Both are permitted for a paired
device token already (`/api/library/*` has no desktop-only gate, unlike the pairing-management
routes), confirmed by reading `auth.py`/`pair.py` before assuming it.

**Idempotent by construction, the actual "no data loss" guarantee.** The source files these
operations touch (`scraped/`, `gender_valid/`, etc.) always originate on the laptop — the pipeline
writes them there first, Syncthing syncs them *down* to the phone for review — so the race is only
ever about the promote/delete decision propagating back *up*, never about the source file itself
being absent. `move()` treats `to` already existing as already-converged (a concurrent Syncthing
catch-up landing the identical file first, or a retried call) rather than an error, trashing any
stray leftover `from` instead of overwriting onto the destination; `to` and `from` both absent is
reported as a per-item error without aborting the rest of the batch. This also makes the whole
mechanism safe under the residual edge case inherent to dual-writing into a bidirectionally-synced
folder: if Syncthing's own upward sync of the identical rename lands moments after (or before) the
agent call, both sides converge on byte-identical content, so at worst Syncthing does a harmless
no-op re-confirmation — never a conflict that could lose a selection.

**Mobile side:** new `services/agent_library_sync.dart` (`libraryRelPath()` + best-effort
`syncLibraryChangeToAgent()`, silently swallowing any `DioException` — unreachable/offline is not
an error state here, it's the expected unpaired case). Wired into `_applyAction`/`_deleteSelected`
in both `folder_screen.dart` and `entity_images_screen.dart`: the local file loops now also collect
the exact rel-path pairs/paths that actually succeeded locally, and the agent sync call is awaited
right before the "Applying…" spinner clears — closing the whole race window before the button
signals done, not a fire-and-forget that could still lose the race.

**Verified:** `agent/tests/test_library.py` grew to 82/82 (6 new unit checks on `ops.move()` — a
real relocation touching nothing else in either directory, the dest-already-exists idempotent
no-op trashing the stray source, both-sides-absent as a reported error not a crash, path-traversal
rejection, and a mixed batch where one bad item doesn't block the rest — plus 2 new REST checks
over the live app). All 15 agent suites green (regression-free). Restarted the real agent (all
three supervised services confirmed still `adopted`, uptime intact) and smoke-tested
`POST /api/library/move` against a deliberately nonexistent path — confirmed live and reachable
without touching any real file, matching CP 5.2's own precedent of never exercising `apply`/
`delete`-shaped mutations against real `IA_DIR` data from a verification pass. Mobile: `flutter
analyze` clean (mobile repo's one pre-existing, unrelated `thumbnail_cache.dart` lint, untouched);
built a real debug APK and installed it on the adb-connected test phone — not opened or tapped
through by Claude, per the mobile-reinstall precedent; on-device confirmation is yours to do.

**You tested this live and confirmed it works** — applied a batch on the paired phone, immediately
triggered Reduce reserve, and the pool count landed where expected instead of overshooting.
Committed the same session.

---

## 2026-08-04 (continued) — Mobile's button row: back to evenly-spaced, per your correction

### D89 · The full-width-row split (D87) over-corrected — one evenly-spaced row again, ellipsis instead

**Asked:** with "Run now" gone (D88), mobile's `FlowDetailScreen` was down to at most Trigger now +
Reduce reserve + Stop — D87's fix for the wrapping-text problem (pulling Reduce reserve into its
own full-width row below) no longer read as necessary now that there's real room, and looked more
stacked/uneven than the original side-by-side design ever did with two buttons. Requested: go back
to one evenly-spaced row for every button, on every flow, including when Stop appears — and if a
label doesn't fit, truncate it rather than wrap or stack.

**Chosen:** merged back into a single `Row` of `Expanded` buttons (Trigger now, + Reduce reserve
for entity-follow, + Stop while running), every label wrapped in `maxLines: 1,
overflow: TextOverflow.ellipsis` — the actual fix for D87's original complaint (a label wrapping
onto two lines, taller than its siblings) rather than routing around it with a layout split. A
three-way even share is tighter than D87's dedicated full-width row, so ellipsis is what keeps a
tight share from ever growing uneven again, per your explicit instruction.

**Verified:** `flutter analyze` clean (the one pre-existing, unrelated `thumbnail_cache.dart` lint,
untouched). No test suite exists in this repo (CP 6.4's own precedent) — verified by re-reading the
rendered widget tree logic. Rebuilt and reinstalled on the adb-connected test phone; not
opened/tapped by Claude.

**You tested this live afterward and confirmed it works** — closes the whole D86–D89 arc (Reduce
reserve itself, the two live-caught bugs, the Trigger now rename, and this layout correction) as
checkpoint-tested, not just built. Committed the same session.

---

## 2026-08-04 (continued) — "Run now"/"Skip wait" removed; "Force run" renamed to "Trigger now"

### D88 · A manual trigger only ever means "run it now, regardless of condition" — one button, not two

**Asked:** "Run now"/"Skip wait" (ends an in-progress wait early, re-evaluating the gate now instead
of at the deadline, but doesn't bypass the switch/daily-limit/condition — could still do nothing at
all) and "Force run" (bypasses everything) had coexisted since CP 3.5. Your framing: when you reach
for a manual trigger you already know you're doing it manually, and you always want it to actually
run — the softer, "might still not do anything" distinction never matched how you use these
buttons. Requested: remove "Run now"/"Skip wait" entirely, keep only "Force run" renamed to
"Trigger now", on both clients.

**Chosen — a pure UI change, zero backend logic changes.** `force_run`'s existing bypass-everything
semantics already are exactly "always run regardless of condition" — nothing about the trigger
mechanism needed to change, only which buttons exist and what they're called. The wire command
stays `force_run` and `gate.reason` stays `"forced"` (renaming those would ripple through
`Insta-Automate`'s log messages, `entity_follow`'s tail messaging, and both clients' `gate.reason`
switch statements for zero user-visible benefit) — only the **displayed** text changed: button
label, confirm-dialog title/button, snackbar text, and (for consistency) the gate detail string the
pipeline itself generates (`_trigger_gate()` in `controllers/prefect.py`), which said "triggered via
Force run, bypassing the gate" verbatim and would otherwise have kept saying the old name right
next to the new button.

**Desktop:** `flow_card.dart` lost `_runNow`/`_runNowLabel` and the "Run now" button entirely;
"Force run" → "Trigger now" (button, and `forceRunFlow`'s dialog in `core/force_run.dart` — function
name kept, since renaming it would be pure churn for a label-only change). `live_page.dart`'s header
button got the same rename. Mobile: `flow_actions.dart` lost `runNow`/`runNowLabel`; `forceRun`'s
dialog copy renamed the same way. `flow_detail_screen.dart`'s button row lost its first slot — since
that row was deliberately equal-width (D67) for a set of similar-length labels, and D87 had already
split Reduce reserve into its own full-width row below it, the remaining row is just Trigger now (+
Stop when running), which needed no further layout rework.

**Verified:** `flutter analyze` clean both apps (mobile's one pre-existing, unrelated
`thumbnail_cache.dart` lint, untouched). Desktop `flutter test` 52/52 — updated the D87 regression
fixture and the "command pending hides the trigger button" assertion to the new label rather than
leaving them silently checking for text that no longer exists. No test suite exists in the mobile
repo (CP 6.4's own precedent). Backend: `Insta-Automate` pushed, rebuilt, scheduler pod restarted
(worker untouched — `_trigger_gate` is scheduler-side only, never runs in a flow body), confirmed
via `kubectl exec` against the scheduler pod's loaded `prefect.py`. Both apps rebuilt and
reinstalled/restarted; neither client's Trigger now button was clicked/tapped by Claude.

---

## 2026-08-04 (continued) — "Reduce reserve": a drain-to-backpressure-target manual trigger for entity-follow

### D86 · A second entity-follow trigger that stops on pool size, not on FOLLOW_BATCH successes

**Asked:** entity-follow's batch stop condition (`FOLLOW_BATCH`, 5 successful follows) doesn't
match what actually gates entity-scrape — `scraped/ + follow_queued/` against
`FOLLOW × SCRAPE_RESERVE_FACTOR` (180 by default). Every image processed gets `unlink()`'d
regardless of outcome (success, already-requested, not-found), so a batch of 5 real follows can
leave the pool barely smaller if most of the batch were skips, or a lot smaller if all 5 hit real
follows on the first try — there was no way to say "just get the pool back under the reserve,
whatever that takes" short of guessing how many times to hit Force run. Requested: a second,
distinct manual trigger, **"Reduce reserve"**, that keeps entity-follow processing the queue —
successes and skips alike — until the pool actually reaches the reserve target.

**Chosen — bypasses the daily FOLLOW limit, like Force run does.** Asked directly rather than
guessed, since it's a real Instagram-rate-limit-safety tradeoff: backpressure and the daily follow
cap are most likely to be hit on the same bad day, and only bypassing the cap lets this trigger
reliably finish what it's asked to do. **Rejected:** stopping early if the daily limit is hit
before the target — safer, but would leave the exact worst-case day (both gates hit at once)
unresolved by the one tool built to resolve it.

**Naming, iterated live with the user rather than picked once:** "Drain to reserve" → "Clear
backpressure"/"Catch up to reserve"/"Unblock scrape" → narrowed to a "remove excess" framing →
**"Reduce reserve"**, the user's own final wording, used verbatim as both the button label and the
wire command name (`reduce_reserve`).

**Implementation — one new command riding the existing generic channel, not a new mechanism.**
`agent/src/ia_agent/scheduler.py::KNOWN_COMMANDS` gained one entry; the REST route and both
Flutter clients' `sendCommand`/`_sendCommand` are already fully generic (any flow/command string),
so no plumbing changes were needed there — only new call sites (buttons + confirm dialogs) and one
new `gate.reason` case in each subtitle switch. In `Insta-Automate`, `entity_follow_trigger()`
(`controllers/prefect.py`) now consumes `reduce_reserve` alongside `force_run` each iteration and
folds it into the existing `force` bool (`force = force_run or reduce_reserve`), so the daily-limit
bypass inside `entity_follow()` falls out for free — `reduce_reserve` itself only changes the
*stop condition*: `flows/entity_follow.py` now computes `pool_count`/`reserve_target` once at
flow start and swaps `followed >= n` for `pool_count > reserve_target` in both the outer `for` and
inner `while`, decrementing `pool_count` by 1 after each `image.unlink()` (cheaper and just as
correct as re-globbing per image — entity-scrape's own trigger is gated off by the same
backpressure check while the pool is above target, so nothing else grows `scraped/` mid-drain, and
a human promotion `scraped/ → follow_queued/` doesn't change the sum either). `wait_until()`/
`wait_day_change()` both got `reduce_reserve` added to their existing `force_run` peek, so a
queued command wakes an in-progress wait immediately, matching `force_run`'s behavior exactly.

**Verified:** a throwaway script (`scratchpad/check_reduce_reserve.py`, matching this repo's
established no-test-suite precedent) calls the real `entity_follow.fn(...)` directly — bypassing
the Prefect engine entirely via Prefect's own `.fn` escape hatch, so no API/orchestration context
is needed — against a scratch directory with every heavy dependency (Postgres, device, Telegram,
the agent, `db_backup`, `rm_empty_subdirs`) monkeypatched to fakes, never touching the real
`IA_DIR`. 7/7 checks: normal batch mode unaffected (stops at `n` regardless of pool size), reduce
mode stops at *exactly* the target regardless of the success/skip mix scripted into
`profile_follow`, and both an at-target and a below-target pool are correct no-ops. Agent:
`agent/tests/test_scheduler.py` extended to 25/25 (one new check — `reduce_reserve` is accepted,
not 400'd); all ten other agent suites re-run clean, no regressions. Desktop: `flutter analyze`
clean, `flutter test` 51/51, `flutter build windows --debug` succeeds — built and started for you
per rule 5, not clicked by Claude. Mobile: `flutter analyze` clean (the one pre-existing
`thumbnail_cache.dart` lint, untouched, same as D84/D85), built a real debug APK and installed it
on the adb-connected test phone — **not** navigated or tapped through afterward, per the
established mobile-reinstall precedent of leaving on-device interaction to the user. One real risk
flagged rather than assumed away: mobile's `FlowDetailScreen` button row can now hold up to 4
`Expanded` buttons at once (Run now/Skip wait, Force run, Reduce reserve, Stop) on a phone-width
screen — worth a look on the real device before calling this done. Neither `Insta-Automate` nor
either Flutter client's Reduce reserve action was actually triggered against live data — same
standing precedent as CP 5.2/CP 7.1 for a real, consequential action.

**Deployment:** `Insta-Automate`'s `feat/control-center` branch pushed, `ia build`'d, and rolled
out to both the scheduler and worker pods (the worker needed a real rebuild + restart, not just a
rollout, since `entity_follow()`'s signature changed — D39/D82's established gap between "rolled
out" and "actually running the new code"), confirmed via `kubectl exec` against the worker pod's
loaded `entity_follow.py`. Standing redeploy permission used, not asked again.

---

## 2026-08-04 (continued) — D86's own checkpoint test caught two real bugs plus one deploy gap

### D87 · The agent itself was never restarted; a fixed-height box silently clipped a second button row on desktop; mobile's equal-width row didn't scale to a longer label

**Asked implicitly — you tried the feature live within minutes of D86 landing** and hit it from
both ends: mobile's Reduce reserve button answered `unknown command: reduce_reserve`, and
desktop's FlowCard rendered the button unclickable, overlapping the "Last run" line below it.

**Bug 1 — the running `ia-agent.exe` never picked up its own code change.** D86's deploy section
carefully rebuilt and restarted both `Insta-Automate` pods, but never touched the agent process
itself — the one place `KNOWN_COMMANDS` actually lives. This is the exact "the code changed, the
running process didn't" gap CP 4.4 first hit and every checkpoint since has had to remember (D21's
own launcher exists because of it) — this session forgot it applies to the agent's *own* source,
not just the pipeline's. **Fixed** with a plain `taskkill /F /IM ia-agent.exe` (not the `schtasks`
cycle D73 showed loses service adoption) — the launcher respawned it in seconds, all three
supervised services confirmed still `adopted` across the restart. Verified `reduce_reserve` is now
accepted by queuing it against `entity-scan`, a flow whose trigger loop never consumes that
command name — proves the whitelist without triggering anything real.

**Bug 2 — desktop's button row sat in a `SizedBox(height: 36)` sized for exactly one row.**
Four buttons at once (Run now, Force run, Reduce reserve, Stop) wrap the `Wrap` to a second row,
but a `Wrap` given a *tight* height constraint doesn't throw the way `Row`/`Column` overflow does
— it just paints the second row outside its allotted box. Every existing `flows_layout_test.dart`
case asserts `tester.takeException()` is null, which is exactly why none of them caught this: there
was nothing to catch. **Fixed** by sizing the row to its content instead of a fixed height — a
`Column` sizes to whatever its children need, so nothing else had to change. **Verified as a real
regression, not assumed**: deliberately reintroduced the fixed-height wrapper, confirmed the new
test (`entity-follow with all four buttons at once`, asserting the "Last run" text's real
`dy` sits at or below the last button's, not just `takeException()`) fails against it
(`254.0 < 338.0`, a real overlap), then confirmed it passes again once reverted to the fix.
`flutter test` 52/52 (51 prior + 1 new).

**Bug 3 (a UX regression, not a crash) — mobile's equal-width `Row` of `Expanded` buttons doesn't
scale to a longer fourth label.** That design was deliberate (D67: "every button shares the row's
width equally… so Run now and Force run always render the same size as each other") for a set of
short, similar-length labels — "Reduce reserve" wrapped onto two lines at a third/quarter share,
rendering taller than its siblings. **Fixed** by splitting into two rows instead of switching to a
`Wrap` (which would have made every button's width inconsistent, not just the new one): the
original equal-width row stays exactly as before (Run now, Force run, Stop), and Reduce reserve —
a heavier, rarer, follow-only action that bypasses the daily limit anyway — gets a full-width row
of its own below, visually distinct from the routine actions rather than squeezed in as a peer.
`flutter analyze` clean (the one pre-existing `thumbnail_cache.dart` lint, untouched); no test
suite exists in this repo (CP 6.4's own precedent) so verified by re-reading the rendered widget
tree logic rather than a test.

**Deployed:** desktop rebuilt, all five running instances from earlier sessions killed and a
single fresh one started (accumulated clutter, not a bug — cleaned up so you're not looking at a
stale window). Mobile rebuilt and reinstalled on the adb-connected test phone. Neither app's Reduce
reserve button was clicked/tapped by Claude — same standing precedent as D86, now doubly relevant
since the underlying command is confirmed live and would actually fire a real drain.

---

## 2026-08-04 — Live-flow result cards: click opens the subject, right-click/long-press opens the root

### D85 · Click-to-open-profile added to all five Live-flow result surfaces, on both clients

**Asked:** the Live screen's (and mobile `FlowDetailScreen`'s) per-item result cards — the same
five surfaces CP 4.4/CP 6.4 built (Scan, Classify, Scrape, Follow, Ingest) — had no click
interaction at all. Requested: clicking a card opens that item's own Instagram profile; a
long-press opens the *root* entity's profile (the entity a Scrape/Follow candidate was found
under, already shown as "root: `<entity>`" via `rootFromImage()`) — a no-op when there's no root.
Also asked, explicitly: how "long press" should map to a mouse on Windows.

**Chosen — right-click is the desktop mapping for long-press, direct action, no menu.** This
repo already has an established precedent for exactly this pairing: the Library screen maps
mobile's touch long-press (`entity_card.dart`'s "Hold to open Instagram") to right-click
(`library_tile.dart`'s `onSecondaryTapDown`) for the desktop. Kept that same mapping here rather
than a literal click-and-hold — `GestureDetector.onLongPress` technically does fire for a held
mouse button too, but it isn't a discoverable desktop idiom and would diverge from what Library
already ships. Confirmed with the user as a direct single action (open the root profile
immediately) rather than Library's richer right-click-opens-a-menu pattern, since only one action
is needed here.

**Scope — all five surfaces, root gesture only fires where a root exists.** Scan/Classify/Ingest
have a subject but no root concept at all (confirmed by reading `rootFromImage()`'s own doc
comment and each surface's fields — only `scrape_queued/<root>/<user>.jpg` and
`follow_queued/<root>/<user>.jpg` carry one); those three get left-click-to-open-subject only,
with no right-click/long-press handler attached at all — not a handler that's attached and then
does nothing, so there's no dead click/vibration on a card with no root. Scrape and Follow get
both gestures.

**Implementation — one shared wrapper widget per app, not per-surface gesture code.** Both
`surface_common.dart` files (desktop `app/lib/features/live/surfaces/`, mobile
`flutter/Insta-Automate-Client/lib/widgets/flow_surfaces/`) gained a `ResultCardActions` widget:
`subject`/`root` in, wraps `child` with the platform gesture pair, resolves via the existing
`instagramUrl()`/`instagramUri()` helper (already shared/mirrored across both apps and the
pipeline per its own doc comment) and opens it — `FileOpener.openUrl()` +
`AppSnackBar` on the desktop, `url_launcher`'s `launchUrl()` + a plain `ScaffoldMessenger` snackbar
on mobile, matching each app's own existing pattern for this exact action
(`library_tile.dart`/`entity_card.dart`). Either gesture is `null` (unregistered, not a no-op
callback) when its target is `null`. Wired into all five surface files on both apps around each
card's existing subject/root computation — no new state, no changed layout.

**Verified:** `flutter analyze` clean on both apps (one pre-existing, unrelated
`unnecessary_import` lint in mobile's `thumbnail_cache.dart`, untouched here). Desktop
`flutter test` 52/52, unchanged — no test needed new fixtures since no layout changed, only a
gesture wrapper added around existing widgets. No test suite exists in the mobile repo (CP 6.4's
own precedent). Desktop: `flutter build windows --debug` succeeds, built and started for you per
rule 5. Mobile: built a real debug APK and installed it on the adb-connected test phone (D57's
ground rules — that phone's `IA_DIR` is stale, fine for exercising app logic). **You tested both
clients live and confirmed everything worked** — click-to-open-subject and right-click/long-press-
to-open-root both behave as designed on desktop and mobile.

---

## 2026-08-04 — Flows screen: separating "poll" from "trigger" from "cooldown"

### D84 · FlowCard's single countdown ring conflated three different waits — split into a mechanism line, a blocked state, and a cooldown-only ring

**Found:** you flagged the Flows screen (screenshot attached) as looking "odd" — every flow card
shows one countdown ring, but the ring's number is really just whichever `wait_until()` call the
trigger loop (`Insta-Automate/controllers/prefect.py`) happens to be sleeping through, and that
loop reuses the same mechanism for two conceptually unrelated things: the fast poll that rechecks
a condition, and (for Scrape/Follow) a genuine mandatory cooldown enforced after a real run. The
Scrape card's own screenshot showed this directly — `0:08`, `SCRAPE_BUFFER`'s poll tick, while
gated by backpressure — reading exactly like "runs in 8s" when it wouldn't.

**Root cause, confirmed by reading the trigger loops directly, not guessed:** every flow's loop
only ever emits `phase` (`idle`/`running`/`waiting`/`day_paused`), a `gate` (`ok`/`reason`/
`detail`), and `next_trigger_at`. `wait_until()` — reused for every kind of wait — never touches
`gate`, only `phase`/`next_trigger_at`. So a false condition (waiting to recheck) and a just-ran
mandatory cooldown (`SCRAPE_WAIT`/`FOLLOW_WAIT`, chained before the trailing poll buffer) both
render identically: `phase: "waiting"`, `gate.ok: true` (a leftover from the trigger that just
fired), `next_trigger_at` some future instant. You confirmed the pipeline's own trigger/poll/
cooldown/daily-limit logic is correct — the gap is entirely in how the control center represents
state that already exists, except for this one missing distinction.

**Chosen, cross-repo:**
- **Insta-Automate (`feat/control-center`, `controllers/prefect.py`):** one additive
  `self._set_state(flow, gate=_gate(True, "cooldown", ...))` call added right before each of
  `entity_scan_trigger`/`entity_scrape_trigger`/`entity_follow_trigger`'s post-run
  `wait_until(..., "*_WAIT")`. Since `wait_until` never touches `gate`, this one line covers the
  whole cooldown stretch (including the trailing poll-buffer chained after it) with no trigger
  logic changed — the same additive, state-only-reporting pattern as the existing `"forced"`/
  `"message"` gate reasons. Ingest's instant path already tagged `gate.reason: "message"` on a
  Telegram-triggered run (D66) — no change needed there.
- **Control center (`FlowCard`):** replaced "one ring = `next_trigger_at`" with three explicit
  things. (1) An always-visible, config-driven mechanism line per card — e.g. Scrape's reads
  "Runs when scraped+follow_queued is below the reserve · checked every 10s · min 10m between
  runs" — naming the condition, poll cadence, and cooldown as three separate facts instead of one
  ambiguous number. (2) A **blocked** state (`gate.ok == false`, day-paused excluded): no ring at
  all, just a static icon and the gate's own `detail` text as the headline — a countdown here
  implies "runs at 0," which is false. (3) A **cooldown** state (`gate.reason == "cooldown"`): the
  only state that keeps the big animated ring, relabeled "Cooling down" — the one wait that really
  is a deterministic "eligible again at X." A **polling** state (condition true, no cooldown —
  Ingest/Classify/Scan's ordinary case) gets a static refresh icon, no live-decrementing number,
  since polling every 10s doesn't need per-second animation. `Running`'s subtitle now also names
  *why* it's running when the gate says so (`"Running · triggered by message"` /
  `"Running · forced"`), reusing gate reasons that already existed but were never surfaced.

**Rejected:** teaching the pipeline to emit a new structured "mechanism" object (condition text +
poll/cooldown seconds) instead of one gate-reason string, and/or moving the per-flow mechanism
metadata into a shared model in `scheduler_models.dart`. Neither pulled its weight: the poll/
cooldown *seconds* already exist as ordinary config (`SCAN_POLL_WAIT`, `SCRAPE_WAIT`, etc.,
Settings > Limits > Timings since CP 3.5) that `FlowCard` can read directly, and the condition
*text* is static per-flow knowledge with nowhere else in the app that needs it — matching how
`flowTitle`/`_todayLine()` already hardcode per-flow formatting in this exact file rather than
fetching it from the backend.

**Verified:** Insta-Automate — `uv run python -c "import insta_automate.controllers.prefect"` and
`ruff check` both clean (no test suite there, same precedent as every prior checkpoint in that
repo). Unlike every other undeployed `feat/control-center` change to date, this one was pushed,
rebuilt (`ia build`), and rolled out to the real scheduler pod the same session — needed so you
could actually see the cooldown state live rather than a dead code path — and the live pod's
loaded source was inspected directly (`kubectl exec` + `inspect.getsource`, D39's precedent) to
confirm all three trigger loops carry the `"cooldown"` gate, not just a healthy rollout. Control
center — `flutter analyze` clean, `flutter test` all green (52 — 48 prior + 4 new cases in
`flows_layout_test.dart` covering the blocked/cooldown/mechanism-line/instant-path states). Two
existing suites needed a `ConfigController` fake added alongside their existing fakes
(`flows_layout_test.dart`, and `overview_layout_test.dart` since `OverviewPage` embeds `FlowCard`
directly per D79) — without it, `FlowCard`'s new mechanism line triggers a real `dio.get
('/api/config')` with no override, which left a pending `Timer` past test teardown and failed the
suite (the same class of gap `ops_layout_test.dart`'s own offline Dio adapter, noted in CP 7.3,
exists to avoid). **Not yet live-tested against the real UI** — built and started for you per rule
5; awaiting your check that the new mechanism line, blocked/cooldown states, and running-reason
subtitle read correctly against the real pipeline.

**Addendum, same day: the mobile client (`ia_manager`) had the identical bug.**
`FlowDetailScreen`'s header (`flutter/Insta-Automate-Client`, `feat/lan-agent`) showed "next
trigger in mm:ss" any time `phase == 'waiting'`, including while blocked on backpressure/no_work —
the same false claim, just as text instead of a ring. You scoped this explicitly to the core fix
only, not full parity: no always-visible mechanism line (that would need new config-reading
plumbing — `EnvService.kLimitDefaults` doesn't carry the eight timing keys today, only the nine
limit ones), just the same blocked-vs-cooldown split. New `flowStatusKind()` in
`utils/flow_phase.dart` mirrors the desktop's `_StatusKind`/`_kindOf` exactly (off/running/
day_paused/cooldown/blocked/polling); `FlowDetailScreen`'s `_Header` only shows a countdown for
`FlowStatusKind.cooldown`, relabels the subtitle per kind, and — free, from data already on
`FlowState` — names *why* a run is in progress (`"Running · triggered by message"` /
`"Running · forced"`). `flowPhaseColor` (shared with `LiveFlowStrip`'s compact chips) now gives
blocked its own amber tint instead of the same primary tint an ordinary poll wait gets, so even
the home-screen strip hints something needs a look before you tap through.

**Verified:** `flutter analyze` clean (one pre-existing, unrelated `unnecessary_import` lint in
`thumbnail_cache.dart`, not touched here). No test suite exists in this repo (matches CP 6.4's own
precedent). Built a real debug APK and installed it on the adb-connected test phone — per D57's
ground rules, that phone's `IA_DIR` is stale and not the production sync target, so it's good for
exercising the app's own logic but the scheduler state it shows is whatever the real agent reports,
same as before. **Not yet opened/verified on the phone** — per the mobile-reinstall-setup
precedent, the install is done and handed over rather than tapped through by the agent.

---

## 2026-08-03 — Live bug-fixing pass: missing not-found events, kubectl wrapper casing

A new post-acceptance bug-fixing session (Phase 7 is done; these are ordinary bugs found live, not
checkpoint work) — first of what you expect to be several, one at a time.

### D82 · `profile_scrape`/`profile_follow` emit nothing at all for a "Profile not found" profile

**Found:** your own live screenshot — the run log showed 18 profiles processed
("Scrape complete. Processed: 18, Scraped: 10") but the Live screen's own counter read
`processed: 16`. Two profiles in that run hit `@{id}: Profile not found` (a deactivated/deleted
Instagram account) — a case genuinely different from D64/D68's PRIVATE/PUBLIC/UNAVAILABLE checks,
since the profile page never loads at all here.

**Root cause:** `tasks/ia.py`'s device-open retry loop (identical in both `profile_scrape` and
`profile_follow`) returns `False` from inside the loop, before either function's own
`scrape.started`/`follow.attempt` emit — the only early-return branch in either function with no
`emit()` call at all. `run_summary.dart`'s `_liveCounters` tallies `entity-scrape` as
`scrape.done`/`scrape.skipped` events and `entity-follow` as `follow.result` verdicts, purely from
the per-item event stream (D40/D41) — a profile that emits nothing is invisible to it, even though
the flow's own `processed` counter increments unconditionally for every queued file.

**Chosen:** move `scrape.started`/`follow.attempt` to fire the instant the attempt is triggered
(before `device.open_entity`), not after the page loads — matching the log line's own "Scrape/
Follow triggered" timing — and add the missing `scrape.skipped` (`reason: "NOT_FOUND"`) /
`follow.result` (`verdict: "FAILED", reason: "NOT_FOUND"`) emit on the not-found path, matching the
shape every sibling skip/failure branch already uses.

**Also folds in a second, related gap you flagged from the same screenshot:** the Live screen's
"attempting…" card for a triggered profile only ever appeared once the profile page had already
loaded — a profile stuck retrying (or one that's about to hit the not-found path) showed nothing on
the display side even though the log already said "Follow triggered." Moving the emit earlier fixes
both at once: every triggered attempt now shows up immediately, and the not-found case's resolution
event has an existing card to resolve instead of never having appeared.

**No Flutter change needed** — `ScrapeSurface`/`FollowSurface` already group events by subject and
render an "attempting…"/in-progress state whenever a `started`/`attempt` event exists without a
resolution yet (checked before writing any pipeline code, not assumed).

**Verified:** import sanity check (no test suite in `Insta-Automate`, same precedent as every prior
checkpoint there). Deployed live via the ops panel's own jobs (see D83 below for why that took two
tries) — `ia build` succeeded, `restart_worker` succeeded (rollout restart → rollout status →
`ia prefect deploy`, all 6 deployments re-registered), and the worker pod's actually-loaded
`profile_scrape` source was inspected directly via `kubectl exec` + `inspect.getsource` to confirm
the real deployed code has both the moved emit and the new `NOT_FOUND` branch (D39's lesson — a
healthy deploy doesn't prove the right code loaded). **You retested live and confirmed a real
not-found profile now shows SKIPPED with the NOT_FOUND reason on the Live screen.**

### D83 · Ops `restart_scheduler`/`restart_worker` jobs never actually worked — `shutil.which()`'s casing trips Rancher Desktop's kubectl wrapper

**Found:** deploying D82 above via the ops panel's "Restart worker" job — it failed instantly with
`Error: unknown command "rollout" for "kubectl.EXE"`. Neither `restart_scheduler` nor
`restart_worker` had ever actually been run end-to-end before this (CP 7.1's checkpoint test only
exercised `db_backup`/`reset_pool`; every real worker/scheduler restart up through D74 was done via
a manual shell `kubectl` command, never through the ops panel's own job).

**Root cause:** `ops/jobs.py`'s `KUBECTL = shutil.which("kubectl") or "kubectl"` resolves via
`PATHEXT` (`.EXE`, uppercase by Windows default) to `...\kubectl.EXE` — a different literal string
than the real on-disk `kubectl.exe`. Rancher Desktop's `kubectl.exe` is itself a version-manager
wrapper (`kuberlr`-style: caches multiple real kubectl binaries, picks the one matching the cluster's
server version) that inspects its own invoked path/casing to decide whether to proxy straight
through to the real kubectl or expose its own management subcommands (`bins`/`get`/`version`/...).
Invoked with the wrong-cased path it silently falls into the latter mode — confirmed directly by
invoking the identical file both ways: `kubectl.EXE rollout restart ...` → wrapper's own "unknown
command" error; `kubectl.exe rollout restart ...` → real kubectl's own `rollout` error output. Only
`_kubectl_step`-based jobs were affected — `build`/`deploy`/`db_backup`/`reset_pool` all shell out
via `_ia_step`/`_prefect_k3s_step` instead, never touching `KUBECTL`.

**Chosen:** `KUBECTL = os.path.normcase(shutil.which("kubectl") or "kubectl")` — `normcase` lowercases
the whole path on Windows, restoring the real casing regardless of what `PATHEXT` happens to supply.
**Rejected:** hardcoding the real kubectl path, or special-casing Rancher Desktop's wrapper somehow
— `normcase` is a one-line, generically-correct fix for the actual cause (a `shutil.which` casing
quirk), not a workaround aimed at this one wrapper's particular behavior.

**Verified:** `test_ops.py` 47/47 unaffected. Live, twice: `restart_worker` reproducibly failed with
the bug present, then — after restarting the agent to load the fix (a plain `taskkill /F`, all three
supervised services confirmed still `adopted` with uptime intact across it) — succeeded cleanly
end to end (`kubectl rollout restart` → `kubectl rollout status` → `ia prefect deploy`, all 6 flows
re-registered), which is also what deployed D82 above to the real worker pod.

---

## 2026-08-03 — Closing out what's pending post-Phase-7

CP 7.3's checkpoint test is accepted as complete by your own explicit call (you'd already run an
initial pass; you're not planning to go back through the rest, future gaps become ordinary bug
fixes instead). Open questions Q2/Q9/Q10/Q11 are left exactly as-is — no workflow change — and Q5
(Force run) is confirmed working as expected, closing it out alongside the others already marked
✅ in PLAN.md. Phase 8 (Hardening: firewall automation, TLS/SPKI pinning, agent self-update, crash
reporting, secret rotation) is explicitly out of scope — everything here is local-only, so the
hardening concerns it addresses don't apply. Of the two flagged-but-unfixed gaps from the CP
7.1–7.3 sessions, D76's duplicate (below) was judged significant enough to fix; D73's restart-path
gap was judged a narrow edge case not worth code changes — see its own entry for why, and the note
added to `CLAUDE.md`'s CP 2.6 paragraph recording the caveat.

### D81 · The D76 bug also lived in CP 5.4's per-entity dialog — fixed the same way, `scraped`/`followed` dropped entirely

D76 (CP 7.2) fixed `insights.py`'s whole-library funnel and per-entity ranking, but flagged rather
than fixed the identical bug in `library/entity_view.py::fetch()` — the Library screen's
per-entity yield dialog, CP 5.4, already-accepted code, out of that session's ask. Same root cause:
`profile_scrape` writes its `user` row *before* the four skip checks (PUBLIC/NO_POSTS/FMIN/FMAX),
so `count(*) from "user" where root = :root` counts every profile whose stats were read, not just
real scrapes — inflating `scraped`, and `followed_est` (derived from it as
`scraped − in_scraped_folder − in_follow_queued_folder`) inherited the same inflation.

Judged worth fixing now (unlike D73 below): this is a live, user-visible accuracy bug in a feature
actually used to judge an entity's yield, not a rare edge case, and the fix pattern was already
established by D76 — no new design work. Same conclusion applies here as it did for `ranking()`:
`Scrape.scraped`/`Follow.followed` are global daily counters with no entity attached, so there is
no accurate per-entity source for either number without a pipeline schema change (the same
cross-repo cost D49 already declined for real follow-tracking). Rather than relabel or partially
fix it, `entity_view.fetch()` now matches `ranking()` exactly: `scraped`, `in_scraped_folder`,
`in_follow_queued_folder`, and `followed_est` are gone from the response entirely, leaving only the
real per-entity `scanned`/`private`/`female`/`male`. `library.py`'s route no longer passes
`LibraryCounts` into `fetch()` since nothing in it needs folder counts anymore. The Flutter dialog
(`entity_yield_dialog.dart`) drops the "Scraped" and "Followed (est.)" funnel bars and adds a one-
line note pointing at the Insights screen for real whole-library totals; `EntityYield`
(`entity_yield_models.dart`) drops the four fields to match.

**Verified:** `agent/tests/test_entity_view.py` rewritten (13/13 — a `"user"` table is still seeded
in the fixture specifically to prove `fetch()` no longer reads it), all 15 agent suites green
(541/541). `flutter analyze` clean, `flutter test` 48/48 (`entity_yield_layout_test.dart`'s two
cases updated to the smaller `EntityYield` constructor, no new/removed cases). Verified against the
real running agent and Postgres — restarted via a plain `taskkill /F` (all three supervised
services confirmed still `origin: "adopted"`, `restart_count: 0`, uptime intact across it, matching
D74's finding rather than D73's): `GET /api/library/entity/sejjjalll/yield` before the restart
still showed the old `scraped: 365, followed_est: 365` shape (confirming the old code was live and
the bug was real), and after the restart returns only
`{scanned: 2529, private: 1544, female: 1044, male: 500}` — no `scraped`/`followed_est` key at all.

### D73-addendum · Restart-path gap judged low-significance, documented rather than fixed

Re-assessed alongside D81 above, at your explicit ask to weigh whether it's "very important." The
gap only reproduces when cycling the *entire* `ia-agent` scheduled task (`schtasks`) — the specific
maintenance action D73 needed to force the launcher to re-read fresh environment variables, not
something that happens during normal operation. Every more common restart path — killing
`ia-agent.exe` directly, `taskkill /F`, `/F /T`, restarting from the app itself — was re-verified
working correctly both at the time (D74) and again live during D81's own verification above (all
three services stayed `adopted` across a plain `taskkill /F`). Conclusion: this is a documentation-
accuracy gap in CLAUDE.md's blanket "survives the agent dying, any way" claim, not a code bug worth
active fix effort — a caveat naming the one path where it doesn't hold is enough. Left uninvestigated
for *why* `schtasks` cycling differs; revisit if it turns out to matter more than expected.

---

## 2026-08-03 (continued) — CP 7.3 (Polish), built, awaiting your checkpoint test

### D80 · Five real implementation snags, none of them design questions

Found and fixed while building, not scoping decisions: (1) `tray_manager.setIcon()` loads a
**Flutter asset**, not the Win32 `.ico` resource `windows/runner/resources/app_icon.ico` already
embeds via `Runner.rc` — the plan's "no new asset needed" assumption was wrong; fixed by copying
the same file to `assets/tray_icon.ico` and declaring it. (2) Riverpod's `Override` type isn't
exported from `flutter_riverpod`'s public barrel file, so a helper function typed `List<Override>`
doesn't compile outside the package itself — `overview_layout_test.dart`'s override list is built
inline inside an untyped `_pump()` helper instead (Dart infers the list's type without ever needing
to spell out the name), matching how every other layout test in this app already inlines its
overrides rather than factoring them out. (3) `OverviewPage`'s "nothing has reported in yet" test
initially failed to find the notifications section's empty-state text — a plain `ListView`'s
sliver children outside the viewport's cache extent are never built at all, empty-state or not, so
the test now scrolls there first (`dragUntilVisible`) rather than dropping the assertion. (4)
`ServiceState.color()`/`DependencyLevel.color()` both took a bare `ColorScheme`, but the new
`AppPalette` extension lives on `ThemeData` — every call site (`flow_card.dart`,
`dependencies_tab.dart`, `service_tile.dart`, `service_detail.dart`, `status_dot.dart`,
`title_bar.dart`) had `theme` in scope already, so this was a mechanical signature change, not a
design fork. (5) Every existing `flutter test` file builds its own bare `ThemeData()` with no
`AppPalette` registered — rather than touch a dozen test files, `ThemeData.palette` falls back to
`AppPalette.dark` when the extension isn't found, which is the correct value there too (this app
is dark-only), not a workaround.

### D79 · CP 7.3 scope and every design fork checked with you before writing code

**Overview built as part of this checkpoint, not split out** — ARCHITECTURE §9 describes it as
"mission control" (five flow rings, three service pills, a dependency strip, burn-down bars, a
device thumbnail, the notification feed) but CP 7.3's own bullet list never mentions building it,
and it's been CP 0.3's bare placeholder ever since. You confirmed it belongs here: every piece of
data it needs already exists behind an endpoint from Phases 2–7, so it's composition, not new
plumbing — `features/overview/overview_page.dart` reuses `FlowCard`, `ServiceTile`, `BurndownCard`,
`DeviceBar`, and (made public for this, same precedent as `FunnelStage`/D77 and `DependencyRow`)
`NotificationTile` directly rather than rebuilding smaller versions of any of them. Each section
header jumps to the matching full destination via a new `selectedNavIndexProvider`
(`core/nav_state.dart`) — `AppShell`'s selected tab moved out of local `State` into a provider
specifically so a page other than the shell itself can change it.

**Tray + hotkey**: `tray_manager` + `hotkey_manager`, both from the same author/family as
`window_manager` (already a dependency) — confirmed with you over `system_tray` for exactly that
consistency. Global hotkey **Ctrl+Alt+I** toggles the window; the tray menu shows Show/Hide, each
flow's phase as a disabled glance row, Start/Stop for each of the 3 supervised services (skipped
for a running-but-external service, since take-over needs more than a tray click can safely
confirm), and Quit. **A real behavior change follows from having a tray icon at all**: the title
bar's close button (`title_bar.dart`, still plain `windowManager.close()`, unchanged) now hides to
tray instead of exiting, via `windowManager.setPreventClose(true)` plus a new
`CloseToTrayListener` (`shell/window_lifecycle.dart`) — a global hotkey and a tray icon both need
something still running to bring back. Real quit is the tray menu's Quit entry, which flips
`setPreventClose` back off first.

**Theming**: the already-informal dark palette (status colors duplicated between
`ServiceState.color()` and `flow_card.dart`'s `_statusColor`, plus a third copy found in
`DependencyLevel.color()` not previously noticed; the service terminal's full ANSI set; the title
bar's connection dot) centralized into one `ThemeExtension<AppPalette>`
(`core/app_theme.dart`), registered on `app.dart`'s existing `darkTheme`. Confirmed with you:
dark-only, no light theme, no toggle — the app was never asked to support one, and Mica plus the
terminal-heavy UI assume it.

**Onboarding**: a single one-time welcome dialog (`core/onboarding.dart`, `shared_preferences`
flag mirroring `MutedTagsController`'s exact pattern), not a multi-step guided tour — confirmed as
proportionate for a single-user app. Re-openable any time via a new "?" affordance in the title
bar, which also opens the shortcut cheat sheet directly.

**Shared empty/error/loading states**: `core/async_state_view.dart` generalizes the shape
`ops_tab.dart`'s private `_placeholder` already had (the richest of several near-identical copies
found across the app) into `LoadingView`/`EmptyView`/`ErrorView` plus an `AsyncValue.stateView()`
extension for the common `.when(loading/error/data)` shape with a retry action. Retrofitted into
every page that hand-rolled this — `flows_page.dart`, `services_page.dart` +
`dependencies_tab.dart`, `library_page.dart` (had **no** page-level loading/error handling at all
before this), `library_grid.dart`, `insights_page.dart`, `settings_page.dart` (its config-load
error had no retry button before this), `ops_tab.dart`, `service_terminal.dart`, and
`live_page.dart` (whose header controls silently rendered nothing before the first heartbeat —
now says "Waiting for scheduler data…").

**Checkpoint test: partial, by your own choice — committed anyway.** You did an initial pass
against the real running app and called it good, but explicitly did not run the full checklist
below and said you'd come back to it if needed rather than block the commit on it. Recorded
honestly rather than claimed as a full pass, per rule 4's own "the test is the checkpoint"
standard — this is a deliberate, acknowledged exception, not a skipped step nobody noticed. Still
open, whenever you do come back to it: tray icon's real flow/service state and its Start/Stop
actually reaching the agent; Ctrl+Alt+I from another app; the title bar's close button hiding
rather than exiting, with only the tray's Quit actually exiting; the welcome dialog appearing once
and not on a second launch; "?" (and the title bar's help icon) opening the shortcut list from
anywhere, **including whether it eats a literal "?" typed into a search box** — flagged rather
than assumed, since this is the app's first app-wide keyboard binding; and Overview's section
headers jumping to the right tab.

---

## 2026-08-03 (continued) — Two rounds of live UI feedback on CP 7.2, checkpoint test passed

### D78 · The Funnel tab's flat, all-normalized-to-the-top bars replaced with a real narrowing funnel showing both conversion numbers per stage

You correctly identified a real visualization flaw, not a data bug this time: every stage's bar was
scaled against `scanned` (the top-of-funnel count), so a deep stage's percentage barely moves even
when its *actual* conversion from the stage right before it changes a lot — "2% of scanned" looks
the same whether Followed just had a bad conversion off Scraped or always did.

**Fixed with a real funnel shape, not a fancier bar** (new `features/insights/funnel_chart.dart`):
each stage is a trapezoid whose top edge equals the *previous* stage's width and whose bottom edge
is its own, so the shape reads as one continuous silhouette narrowing stage-by-stage — a
`CustomPainter` draws it directly rather than five independently-scaled `FunnelStage` bars (which
stays exactly as-is for the Library's per-entity dialog, its only remaining consumer). Every stage
is labeled with **both** conversion numbers side by side — "X% of \[previous stage\] · Y% of
total" — since either one alone hides something real: "% of total" answers "how much of the
original pool made it this far" but flattens out for a stage several filters deep; "% of previous"
answers "how much of *this* filter's input survived it" but says nothing about overall scale. A
non-zero stage is floored to a minimum visible width so a genuinely thin tail (Followed at a few
percent) doesn't taper away to an invisible point. No new categorical palette or legend needed —
one hue, one series, per the dataviz skill's own sequential-magnitude guidance — and every value is
already a direct label, so no hover tooltip was added on top of it.

**A real overflow caught before it shipped** (not by `flutter analyze`, D19's precedent again): a
caption's `overflow: TextOverflow.ellipsis` with no `maxLines` doesn't actually truncate anything —
without a line limit, `Text` just wraps instead, which pushed a caption-bearing stage's label past
its fixed segment height. Fixed with `maxLines: 1` on every text line in the label, and the segment
height increased to fit the worst case (three real lines: name+count, conversion, an optional
caption) instead of a guessed number.

**Verified:** `flutter analyze` clean, `flutter test` 47/47 (`insights_layout_test.dart`'s existing
huge-counts/all-zero cases exercised the new chart directly). Confirmed live — this was the
checkpoint test passing.

### D77 · The Ranking table rebuilt by hand after two rounds of feedback — `DataTable` can't make one column absorb extra width while the rest stay fixed

Two real, sequential UI bugs in the Ranking tab, both found by you actually looking at it at the
app's real opening size, neither visible from source alone:

1. **Female was cut off requiring a horizontal scroll despite visible empty space.** Root cause:
   Flutter's `DataTable` shows a checkbox column automatically whenever any row sets
   `onSelectChanged` (used here only to open the entity dialog on tap, not to track selection) —
   pure wasted width — plus its default `columnSpacing`/`horizontalMargin` (56px/24px) are
   generous. First fix: `showCheckboxColumn: false` and tightened spacing.
2. **That wasn't enough, and forcing the table to the window's full width made it worse** — a
   `ConstrainedBox(minWidth: ...)` around the table produced huge, roughly-even gaps between every
   column instead of "squeeze columns closer." Root cause: `DataTable` builds on a `Table` whose
   columns behave like `FlexColumnWidth` once given more width than their intrinsic content needs
   — extra space distributes *between every column*, not as trailing space after the last one.
   There is no public `DataColumn` API to make one column flexible and the rest fixed.

**Fixed by dropping `DataTable` for this table entirely** and hand-building it with `Row`s: Entity
is the only column wrapped in `Expanded` (it's the one column with genuinely variable-length
content), Type/Access/Scanned/Private/Female stay fixed-width `SizedBox`es. Sortable headers
(`_HeaderCell`, tap to sort, arrow icon on the active column) replicate `DataColumn.onSort`'s
behavior by hand since the column widget is gone. The table no longer needs its own horizontal
scroller at all — every column now genuinely fits any width the window can produce.

**A real overflow caught by the layout test, not `flutter analyze`:** the header's sort arrow icon
pushed "Scanned" past its 90px column at the huge-counts test's text metrics — widened the three
metric columns to 120px, wide enough for the longest label plus its arrow.

**Verified:** `flutter analyze` clean, `flutter test` 47/47. Confirmed live across three rounds
(you flagged the cutoff, then the ugly gaps, then confirmed the fixed-Entity-flexible layout was
right).

---

## 2026-08-03 (continued) — Your own checkpoint test caught a real accuracy bug in D75's numbers

### D76 · `scraped`/`followed_est` were built on the wrong Postgres signal — fixed with real, not estimated, totals for the whole-library view; dropped entirely from the per-entity one

Testing D75 immediately, you flagged the "Followed (est.)" number as implausible — it was landing
within a few percent of "Scraped" itself, when your own sense of the pipeline says real follows
are a small fraction of real scrapes. You were right, and the mechanism was findable in
`Insta-Automate`, not a guess: `profile_scrape` (`tasks/ia.py:440-442`) writes the `User` Postgres
row via `user.update(session)` **before** its four skip checks (PUBLIC, NO_POSTS, FMIN, FMAX) —
so `count(*) from "user" WHERE root=...`, what both `entity_view.fetch()` (CP 5.4) and D75's
`ranking()` called "scraped," counts every profile whose stats were *read*, not the ones that
produced a real scraped image. `followed_est`'s subtraction (`scraped − still-pending-in-folders`)
inherits that inflation directly, so it converges toward the same wrong number `scraped` already
was, not toward the real follow count.

**You separately caught the same bug from the other direction**, comparing tabs directly: the
Daily-limits chart's real day counters clearly showed Scrape (100–400/day) far outweighing Follow
(40–60/day), yet the Funnel tab showed both at the same ~14% of scanned — an internal
contradiction between two tabs reading what should have been the same underlying reality.

**The real signal already existed and needed no new instrumentation**: `Scrape.scraped`/
`Follow.followed` (`Insta-Automate/models/scrape.py`, `follow.py`) only increment when
`profile_scrape`/`profile_follow` actually succeed (`entity_scrape.py:66`, `entity_follow.py:64`)
— the exact counters already driving the Daily-limits chart correctly. Their limitation: they are
**global per-day counts with no entity attached**, so they can produce a real whole-library total
(summed across every day) but nothing broken down per entity.

**Resolved with you before writing code, following your own framing** ("scanned/private/female
are accurate, scrape/follow already have a daily count, add them up — isn't this simple"):
- `funnel()` (whole-library, `GET /api/insights/funnel`) now reports **real, non-estimated**
  `scraped`/`followed` — `SUM(scrape.scraped)`/`SUM(follow.followed)` across every day, entirely
  independent of `ranking()`'s per-entity data. No more "(est.)" — it's a real number now.
- `ranking()` (per-entity, `GET /api/insights/ranking`) **drops scraped/followed entirely** —
  offered as an option (relabel as "profiles read" instead) and explicitly declined: no accurate
  per-entity source exists for either number today, so neither is shown there. Only
  `scanned`/`private`/`female`/`male` remain, all genuinely accurate per-entity Postgres counts.
- The Library screen's own CP 5.4 per-entity funnel dialog (`entity_view.fetch()`) has the
  **identical bug** in its own `scraped`/`followed_est` — same `count(*) from "user"` source,
  same inflation — surfaced by fixing this module but not yet fixed itself, since it's Phase 5's
  already-accepted code and changing it wasn't asked for this session. Flagged for you rather than
  changed silently.

**Verified:** `agent/tests/test_insights.py` rewritten (22/22) — the fixture now deliberately
seeds 5 `user`-table rows for one entity with **no arithmetic relationship** to that entity's real
`scrape`/`follow` day-counter rows, so a regression back to the old formula fails loudly instead of
coincidentally matching. All 15 agent suites green. `flutter analyze` clean, `flutter test` 47/47.
Verified against the real running agent and Postgres after restart (services confirmed `adopted`,
uptime intact): **scraped: 12,455, followed: 3,608 — a real ~29% rate**, matching your own stated
sense of the pipeline, replacing the previous ~99% inflated estimate (21,936 vs 21,756).

---

## 2026-08-03 — CP 7.2, Insights: classify-accuracy scoped out before writing code

### D75 · Classify-accuracy sampling dropped from CP 7.2; funnel/ranking/burn-down built as one checkpoint on real, already-persisted data

Before writing any code, one real gap was flagged: PLAN.md's CP 7.2 bundles four views, and
classify-accuracy sampling ("show N random verdicts with their images, mark disagreements") has no
data to sample from — `classify.access`/`classify.gender` events only ever live in the agent's
in-memory `EventStore` ring (CP 4.2), capped and wiped on every restart, so there is no persisted
verdict history today. Building it would mean adding new persistence that only starts accumulating
from whenever it ships, with nothing to show for a while after. Asked before scoping it in or out
rather than guessing — the user judged it not worth building right now (**Rejected**: build
persistence now and ship with an empty/thin sampling view). Matches
[[feedback-scope-over-cross-repo]]'s standing preference for a cheap real answer over new
machinery for a niche feature, extended here to "no machinery at all, drop the feature" rather than
a lesser local approximation, since there's no cheap approximation available for this one.

The other three views turned out to need **no new instrumentation at all**, so they shipped
together as originally planned:

- **Daily limit burn-down** — `Scan`/`Scrape`/`Follow` (`Insta-Automate`'s `insta_automate.models`)
  are already one Postgres row *per calendar day*, kept forever, not overwritten — real multi-day
  history already existed and just needed a query. Confirmed live: `entity-follow` genuinely hit
  its 60/day cap on five of the last seven real days.
- **Whole-library funnel and per-entity ranking** — both are CP 5.4's per-entity `entity_view.fetch()`
  query widened to every entity via one bulk `GROUP BY` (`ia_agent/insights.py::ranking()`) instead
  of looping the per-entity query once per entity — same numbers, one round trip. `funnel()` is
  `ranking()` summed; the ranking table's rows are decoded client-side with the *existing*
  `EntityYield` model (`app/lib/core/entity_yield_models.dart`) since the agent returns the exact
  same per-entity shape, rather than adding a near-duplicate model. Clicking a ranking row reuses
  CP 5.4's `showEntityYieldDialog` unchanged.

Built as one checkpoint/commit (not split into CP 7.2a/b/c), per direct confirmation — the three
views share one Postgres round-trip shape and one visual language (`FunnelStage`, made public and
shared between the Library entity dialog and the new whole-library funnel, rather than duplicated),
so splitting them would have been checkpoint overhead without a real seam to split along.

**A real layout bug caught before it shipped, not by `flutter analyze` (D19's precedent again):** a
first draft of the ranking table nested a vertical `SingleChildScrollView` around a horizontal one
so the table could scroll both ways inside a fixed-height `Card`. The outer vertical scroller hands
its child an *unbounded* height in the scroll direction — exactly what a horizontal scroller then
needs bounded for its own cross axis — a real "unbounded constraint" class bug, not yet exercised
by `flutter test` at the time it was caught (found on inspection, fixed before the layout test was
even written). Fixed by dropping the fixed-height `Card`/vertical-scroller pair entirely: the whole
tab is one `ListView` (search row + table), and only the table itself scrolls horizontally — the
table's own rows just grow the page's scroll content instead of needing a second scroll axis.

The burn-down charts are five single-series bar charts (Scan profiles/reels/posts, Scrape,
Follow), each its own small multiple rather than one multi-series chart — chosen from the dataviz
skill's own form guidance ("compare magnitude, day to day → bar, sequential one hue") and its
series-count ladder: three of the five caps (`PROFILES=10`, `REELS=30`, `SCRAPE=300`) are different
orders of magnitude, so one shared y-axis across them would misrepresent scale, and small multiples
sidesteps that without needing a second axis or a categorical palette at all — each chart has
exactly one series, so the categorical CVD-pairing checks don't apply, and the existing `FunnelStage`
accent hue (`colorScheme.primary`) carries straight over for visual consistency. Each cap renders as
a dashed threshold line with one direct label ("cap"), deliberately distinct from the solid hairline
gridlines per the skill's mark spec.

**Verified:** `agent/tests/test_insights.py` (19/19 — bulk ranking excludes entities with zero
activity, `funnel()` sums `ranking()` exactly, `burndown()` returns real oldest-first multi-day
history and clamps an out-of-range `days=`, then the same shape again over live REST), all 15 agent
suites green (560 checks). `flutter analyze` clean, `flutter test` 47/47 (41 prior + 6 new in
`insights_layout_test.dart` — a 60-char root with six-figure counts, an all-zero funnel, 90 days of
burn-down history, and both tabs' empty states). Verified against the real running agent (restarted
to pick up the new code; all three supervised services confirmed `adopted` with uptime intact
across it, same precedent as every checkpoint since CP 4.4) against the real Postgres database and
`IA_DIR`: 443 entities, 157,091 total scanned, `sejjjalll`'s ranking row matching CP 5.4's own
previously-verified numbers exactly (2529 scanned → 1544 private → 1044 female, 500 male → 365
scraped → 365 followed_est), and real burn-down history showing genuine gaps (Phase 2's flow
switches were off) and real cap hits (`follow: 60` on five of seven recent days).

---

## 2026-08-02 (continued) — CP 7.1, Ops panel: three design forks resolved with the user before writing code

### D71 · One-shot jobs get plain `asyncio.create_subprocess_exec`, not the services' ConPTY; worker restart auto-chains its fix; the token never gets committed

With Phase 6 accepted (D70), Phase 7's first checkpoint turns the manual `ia build`/`helm`/
`kubectl` commands DECISIONS.md's D38/D55/D59/D68 show have repeatedly gone wrong into real app
buttons. Research first (two Explore agents plus direct reads) established: `services/host.py`'s
ConPTY is built for a long-lived, interactive, resizable process adopted across an agent restart —
none of that applies to a one-shot admin command, so `ops/jobs.py` uses plain
`asyncio.create_subprocess_exec` instead, no detached host process or pty needed. The single
`EventBus`/`/ws` socket already treats a "channel" as just a string tag (confirmed: no per-channel
WS routing exists, every subscriber gets everything), so `ops.jobs`/`ops.logs.{id}` needed no new
WS infrastructure. `ia`/`prefect-k3s` aren't on the global PATH (only `helm`/`kubectl` are, via
Rancher Desktop) — `services/registry.py`'s existing direct-venv-exe convention
(`INSTA_AUTOMATE_DIR / ".venv" / "Scripts" / "ia.exe"`) is reused rather than `uv run --project`.

**Three decisions confirmed with the user before writing any code:**
1. **"Restart worker" auto-chains a deploy step** — a composite three-step job (restart → wait
   ready → `ia prefect deploy`) rather than two separate buttons, closing D38's work-pool-orphaning
   gap for good instead of relying on someone noticing and re-running the deploy by hand, the
   pattern that bit D38, D55, and D68 independently.
2. **Job history persists to disk** (`%LOCALAPPDATA%\ia-agent\ops_jobs\`), same D50 reasoning as
   `NotificationStore` — a helm uninstall or db restore's outcome must survive an agent restart, not
   just live in memory until the next one. A job left `running` by a simulated crash is reconciled
   to `interrupted` on load, since the subprocess died with the agent and there is nothing left to
   resume.
3. **The real `IA_AGENT_TOKEN` is never committed to the Helmcharts repo.** `values.yaml` defaults
   both `agent.token` and `gitBranch` to empty; the "Helm upgrade" job reads the real token off this
   machine (`%LOCALAPPDATA%\ia-agent\token`) and injects both via `helm upgrade --set` at deploy
   time — the same security posture already flagged for the Dockerfile plaintext-secrets issue
   (Q10), applied proactively this time instead of after the fact.

**A fourth correction, found while scoping rather than assumed:** the original plan text said to
surface `IA_AGENT_URL` through helm values alongside `IA_AGENT_TOKEN`. Re-reading ARCHITECTURE
§3.3/D26 first: `IA_AGENT_URL` is already a live `Config` key (`config.env`), specifically so it
changes without a pod restart — only `IA_AGENT_TOKEN` (env-only by design) and the informally
adopted `GIT_BRANCH` (not in the original plan at all, but responsible for three separate
incidents once it became a manual patch) actually needed to move. Confirmed against the live pods'
real patched env via `kubectl get deployment -o yaml` rather than trusting CLAUDE.md's own
prose description of the patches: the scheduler carries both `IA_AGENT_TOKEN` and `GIT_BRANCH` on
every container (`kubectl set env` without `-c` touches the whole pod spec, not just the one
container someone had in mind), the worker only ever carried the token. Two small named Helm
templates (`_helpers.tpl`, the chart's first — none existed before) mirror that exactly rather
than guessing one shared shape for both deployments.

**Every `GIT_BRANCH`-sensitive step (build, deploy, helm upgrade) now reads one agent-side
setting** (`IA_OPS_GIT_BRANCH`) instead of trusting whoever's shell happened to have it exported —
this is the actual fix for D55/D59's repeated root cause (a bare local shell silently deploying
`main`), not just a convenience wrapper around the same failure mode.

**Verified:** `agent/tests/test_ops.py` (45/45) — the real `JOB_SPECS` registry checked statically
(ids, confirm flags, secret redaction in the helm-upgrade step's display argv) before being
replaced with synthetic Python-subprocess jobs for step sequencing, failure short-circuiting
(a failed step's later steps never run), the one-job-at-a-time lock, disk persistence across a
fresh `OpsJobStore`, and the simulated-crash reconciliation — then the same shape again over live
REST plus a real WS delivery, still never touching the real `ia`/`helm`/`kubectl`/`prefect-k3s`
binaries. All 14 agent suites green. `helm template --set agent.token=... --set gitBranch=...`
and `helm lint` confirmed the rendered chart matches the live pods' observed shape exactly.
Flutter: `flutter analyze` clean, `flutter test` 41/41 — the 2 new `ops_layout_test.dart` cases
needed a from-scratch offline `HttpClientAdapter` stand-in, a genuine gap found while writing the
test: `_OpsLogPanel` calls `agentClientProvider` directly (same shape as `ServiceTerminal`'s
replay call), and nothing in this codebase had ever widget-tested that path before — a real,
unmocked network request was leaving a pending Dio timer at teardown until the adapter and
`pumpAndSettle` (instead of a fixed-duration `pump`) fixed it.

Verified against the real running agent — restarted to pick up the new code, all three supervised
services confirmed `adopted` with uptime intact across it — `GET /api/ops/specs` returns the real
ten-job registry, `GET /api/ops/jobs` starts empty, an unauthenticated `POST` is rejected.
**Deliberately not exercised live**: no ops job was actually started this session, same CP 5.2
precedent as `apply`/`delete` — these are real actions on the live cluster nothing asked for, left
for the user's own checkpoint test (rule 4).

---

## 2026-08-02 (continued) — CP 7.1 live-tested for real: a four-repo dependency conflict, a genuine window-sizing bug, a real overflow, and a dead Telegram session

### D72 · First real use of the Ops panel found three real bugs and one pre-existing credential problem — none of them hypothetical

You tested CP 7.1 for real within minutes of it starting: ran "Build image" (failed), ran "DB
backup" (failed differently), and flagged the log panel/history visibly running off the bottom of
the window in both screenshots, plus asked for a copy button. All three code issues were real and
got root-caused and fixed; the fourth (Telegram) is a real credential problem outside anything
this session's code touches.

**1. `ia build` failed on a genuine, four-repo dependency conflict — not anything CP 7.1 wrote.**
uv's resolver treats an unpinned git URL and a `@rev`-pinned one for the same package as
conflicting sources, not "compatible until proven otherwise." `wsl-bridge` has pinned `my-modules`
to `94b308a` since D65 — but nobody had actually run `ia build` since then to notice that
`Insta-Automate`'s own unpinned `my-modules` reference now conflicted with it. Pinning
`Insta-Automate`'s side to match only moved the conflict: `prefect-k3s` and `tg-auth` (a direct
runtime import in `docker.py`, not just a dev tool, and **not previously in CLAUDE.md's repo
table at all** — found only by tracing the actual `uv lock` error) both had the same unpinned
reference. Fixed the same way in all three: `Prefect-K3S` and `TG-Auth` each got their own new
`feat/control-center` branch (neither existed before) with `my-modules` pinned to `94b308a`, and
`Insta-Automate`'s `[tool.uv.sources]` points `prefect-k3s`/`tg-auth` at those branches explicitly
— the same "point a feature branch at a feature branch for testing" pattern this project already
uses for `GIT_BRANCH`, reverting to unpinned/main once those branches merge.

**A second, sneakier layer**: even with every repo's `pyproject.toml` correctly aligned, `uv lock`
kept resolving `wsl-bridge` to a stale pre-pin commit. Root cause: `uv lock` reuses a package's
previously-locked resolution when that package's own source declaration hasn't changed, even
across a full `uv cache clean` — `wsl-bridge`'s source entry in `Insta-Automate`'s
`pyproject.toml` never changed (still bare, no rev), so `uv` had no signal to re-resolve it.
Fixed locally with `uv lock --upgrade-package wsl-bridge`. This only mattered for the local `uv
lock`/`uv sync` commands used to verify the fix — `ia build`'s actual Docker step
(`uv pip install git+...`) does a fresh resolution every time with no lockfile involved, so it was
never affected by this specific staleness, only by the real pyproject.toml conflicts above.

**Verified for real, not just reasoned about**: `ia build` run twice — once reproducing the
original conflict exactly, once succeeding end to end (`docker.io/library/insta-automate:
3.6.27-python3.12` built and exported, ~8s) after every fix was committed and pushed to each
repo's `feat/control-center`/GitHub (the Docker build clones fresh from GitHub, so a local-only
fix would have kept failing there even after `uv lock` succeeded locally — checked deliberately
rather than assumed, given D36/D39's exact "local commit isn't deployed" lesson).

**2. `ia db backup` tried to prompt for a Telegram login code and aborted — a real, pre-existing
credential problem, confirmed independent of the ops panel.** Reproduced the identical failure
running `ia tl verify` directly from a plain shell with stdin explicitly closed
(`< /dev/null`) — same "Please enter the code you received: / Aborted." Telethon's `client.start
(phone=...)` only falls back to that interactive re-auth flow when the stored session itself is
no longer recognized as authorized by Telegram's servers; `TELEGRAM_SESSION` is set as a genuine,
correctly-shaped 353-character string (a real system environment variable this machine already
has, not something `.env`-vs-agent-environment loading ever disagreed about — checked and ruled
out). This needs a fresh interactive login (a code sent to your phone) that only you can complete
— not something to script around. **Hardened anyway**: the ops job runner now explicitly passes
`stdin=asyncio.subprocess.DEVNULL` rather than silently inheriting whatever stdin the agent
process happens to have. It already failed fast here specifically because `ia-agent.exe` (a
GUI-subsystem process, D20) has no console to inherit — relying on that accident was fragile; a
future interactive prompt from a differently-launched agent could otherwise hang forever holding
the one-job-at-a-time lock.

**3. The window itself was taller than the visible screen — a real, separate bug from CP 7.1's
own layout, exposed by CP 7.1 for the first time.** `main.dart` sized the window to
`display.size.height` — `screen_retriever`'s full monitor bounds, taskbar included — not the
usable work area. Every earlier tab's content was short enough that the difference never showed;
Ops's denser layout (job buttons + log panel + history) was the first to actually reach that
extra height and get clipped by the taskbar. Fixed using `display.visibleSize`/`visiblePosition`
(the OS work-area rect, confirmed to exist in `screen_retriever_platform_interface` specifically
for this purpose) instead of the full monitor bounds, for both the window's height and its Y
position — falls back to the full bounds only if the platform channel ever returns null for
either.

**4. `OpsTab` had its own, separate, real overflow at the app's 1024×700 floor.** Not visible
until testing at the actual size: ten real job buttons (one three-line description) plus the new
copy-button header pushed the log/history row past the tab's available height by 19px — caught by
`ops_layout_test.dart` immediately once the header was added, not `flutter analyze` (D19's
precedent, again). Fixed the same way D45/D46 fixed an identical class of problem on the Live
screen: cap the button area's height (`ConstrainedBox` + `SingleChildScrollView`, 190px) instead
of letting the `Wrap` claim whatever height ten cards want, guaranteeing the log/history row below
always gets the rest.

**5. Copy button added to the log panel**, per direct request — a small header row with a
`content_copy` icon button that copies every visible line's text to the clipboard, matching
`ServiceTerminal`'s existing `_copyAll` pattern.

**Verified:** `agent/tests/test_ops.py` still 45/45 after the `stdin=DEVNULL` change. Flutter:
`flutter analyze` clean, `flutter test` 41/41 (the `ops_layout_test.dart` case that first caught
the RenderFlex overflow, now passing after the fix). Both the agent (for `stdin=DEVNULL`) and the
app (for the window-sizing/layout/copy-button fixes) were rebuilt and restarted — the three
supervised services confirmed `adopted` with uptime intact across the agent restart, same
precedent as every checkpoint since CP 4.4. `ia build` confirmed working end to end for real, live
(see above) — this is the one non-destructive job actually exercised live this session, since the
user's own test run is what surfaced the bug in the first place; still no destructive job run,
same standing precedent.

---

## 2026-08-03 (continued) — D74 · "Reset work pool" failed on a real PATH gap in the ops job runner

Reported live: `prefect-k3s reset-pool` failed with `FileNotFoundError: [WinError 2] The system
cannot find the file specified` trying to run bare `["prefect", "work-pool", "create", ...]` via
`subprocess.run`. Root cause: `prefect.exe` lives in the same `.venv\Scripts\` folder as
`prefect-k3s.exe` (confirmed on disk) — `reset-pool`'s own code shells out to the bare `prefect`
command name, which only resolves via `PATH`. A normal interactive invocation works because
activating that venv prepends its `Scripts` folder to `PATH`; the ops job runner invokes
`prefect-k3s.exe` by its full path directly, with no such prepend, so the agent's own inherited
`PATH` (which has no reason to include a project-specific venv's `Scripts` folder) left `prefect`
unresolvable. Fixed generally, not just for this one command: `_ia_step`/`_prefect_k3s_step` in
`ops/jobs.py` now prepend their own venv's `Scripts` directory to the subprocess's `PATH`,
mirroring what venv activation does — closes the same class of bug for any other bare-command
shell-out any `ia`/`prefect-k3s` subcommand might do, not just this one instance.

**Verified:** new `test_ops.py` checks (47/47 total) confirm both `_ia_step` and
`_prefect_k3s_step` prepend the correct venv `Scripts` dir. Agent restarted (plain `taskkill`, not
`schtasks` — confirmed all three supervised services stayed `adopted` with uptime intact, unlike
D73's `schtasks` cycle) and `POST /api/ops/jobs {"kind":"reset_pool"}` now succeeds end to end for
real: `No stale workers found in 'default-pool'.` / `Work pool 'default-pool' ready.`

---

## 2026-08-03 — The Telegram user session had two independent, undocumented gaps stacked on top of each other

### D73 · `ia db backup` fixed for real: local env vars and the K8s secret are two separate, never-synced credential stores — and cycling the agent's own launcher has a stale-environment gotcha

Following on from D72's "the session needs a fresh login" conclusion, the user correctly pushed
back: the same `TELEGRAM_*` env var names are already used successfully by the live pipeline for
notifications and (per D49/D50) scheduled db backups, so why would this need a fresh interactive
login at all? Investigating properly rather than re-asserting the earlier conclusion found the
real answer.

**Gap 1 — two independent credential stores, no sync between them.** `tg_auth.controller
.TelegramSecret.get()` (what the pipeline's Docker build bakes into pod env via `docker.py`'s
`*TelegramSecret.get().model_dump_env()`) reads from a **Kubernetes Secret** (`tg-auth`, namespace
`default`) — not from any local file or env var at all. `tg-auth login`'s only effect is
`v1.patch_namespaced_secret(...)`; a `dump_env()` method exists in the same file that would write
a local `.env`, but nothing in the CLI ever calls it — dead code, or never finished. Confirmed via
hash comparison (never printing either secret) that the local Windows `TELEGRAM_SESSION` and the
K8s secret's `TELEGRAM_SESSION` were genuinely different values, and independently verified via
Telethon's `is_user_authorized()` (a pure check, no risk of triggering a code-send) that the K8s
one is live-authorized and the local one is not. So "the pods have always worked" was true and
irrelevant — they were never touching the credential that was actually broken. **Fixed by copying
the K8s secret's current `TELEGRAM_SESSION`/`TELEGRAM_BOT_SESSION` into the local Windows User
environment variables** (`[Environment]::SetEnvironmentVariable`, values piped directly from
`kubectl` and never printed) — no interactive login needed after all, since a valid session already
existed, just not where the local machine was looking for it.

**Gap 2 — found only because the first restart attempt silently didn't work.** Killing just
`ia-agent.exe` and letting D21's launcher (`pythonw.exe`, held in a job object, restarts on any
non-zero exit) respawn it does **not** pick up a registry env var changed after the launcher
itself last started — the respawned process inherits the launcher's own frozen environment, not a
fresh read. Verified by hash-comparing the actual running process's `TELEGRAM_SESSION` (via
`psutil.Process(pid).environ()`) against the K8s value at each step: identical-length garbage
matched what looked like success until an explicit hash comparison caught that it was still the
*old* value. Fixed by cycling the whole scheduled task (`schtasks /End /TN ia-agent` then
`schtasks /Run /TN ia-agent`) rather than just the exe — a genuinely fresh process tree that does
read current registry values.

**A third thing found as a side effect, flagged rather than chased down**: cycling the task this
way did **not** preserve the three supervised services as `adopted` the way CLAUDE.md documents
("a supervised service survives the agent dying, any way — restart, crash, `taskkill /F` or
`/F /T`"). Checked real OS process start times (`Get-Process | Select StartTime`), not just the
agent's self-reported `uptime_s`: `adb`/`vl-server`/`wsl-bridge` all genuinely restarted within
seconds of the task cycling, `adb` came back as `external` rather than `supervised`. No flow was
actively running at the time (checked `GET /api/scheduler` immediately after — all `waiting`,
last runs `COMPLETED`), so nothing was disrupted this time, but this is a real, previously
unverified gap specific to `schtasks /End`+`/Run` (every other restart this whole project has used
a plain `taskkill` of just the exe, which does preserve adoption). Left open — not part of CP 7.1,
and chasing it now would be solving a problem nothing actually hit yet.

**Verified for real:** `POST /api/ops/jobs {"kind":"db_backup"}` through the actual running agent
(the real production path, not a hand-run CLI command) completed with `status: succeeded,
exit_code: 0`, log showing a real Postgres export (6 tables) followed by `Uploading ... to Insta
Backup channel` / `Upload complete. Backup successful.` — a real file landed in the real Telegram
channel. This is now the second non-destructive ops job (after `ia build`, D72) actually exercised
live this session, both because live use is what surfaced the bugs they're fixing, not because
verification needed it.

---

## 2026-08-02 (continued) — Session resume: D68's last open item closed by observation

### D70 · Real scrape runs confirmed completing successfully post-D68, no code change needed

Resuming the session, the live agent's scheduler snapshot and flow-run history were checked before
doing anything else (`GET /api/scheduler`, `GET /api/flow-runs`) — the one thing D69's write-up
flagged as still open was "a real scrape run completing successfully post-D68," verified only
structurally (code loaded, pods healthy, gates sane) at the time, not by watching a real profile
scrape succeed.

That's now observed for real without any intervention: `entity-scrape` shows `today.scraped: 136`
(limit 300), and the two most recent `entity-scrape` flow runs (`d4389a76`, `d5835872`) both show
`COMPLETED` at durations (62s, 71s) matching D55's historical successful-run baseline (92.4s) — real
profiles have been scraping successfully since the fix, unattended, across however many trigger
cycles produced 136 completions. All five flows are gating normally (`entity-scrape` on
backpressure, `entity-follow` on `day_limit` at 70/60 — over the cap, consistent with D25's
documented force-run behavior bypassing the day-limit gate, not a new bug). Device bridge reachable,
mirroring active, all three supervised services reporting healthy. Nothing else needed action.

---

## 2026-08-02 (continued) — Live retesting of D60–D65 found four more real issues, one a production incident

The same session kept going once you started actually exercising the D60–D65 fixes end to end —
each round of testing surfaced something the first pass hadn't, including one bug (D68) that
required uninstalling the live Helm release to stop.

### D69 · Window position needed a real unit conversion, not just a hardcoded offset; plus a Stop button, a real auto-follow bug, and one design revert

**Window position, round two.** D67's first attempt positioned the app next to scrcpy using
scrcpy's own launch geometry (`--window-x=1`, width derived from the phone's aspect ratio at
`--window-height=1480`) fed directly into `windowManager.setPosition`. Still a visible gap after
rebuilding — root cause: those figures are scrcpy's *physical* pixels (a native SDL app), while
`window_manager`/`screen_retriever` both work in Flutter's *logical* pixels. On this machine's
150%-scaled display that's a real ~1.5x error, confirmed by back-calculating the actual on-screen
pixel positions from a screenshot (predicted physical x≈1020 for a logical x=680 target, observed
≈1039 — matching the scale factor almost exactly). Fixed by dividing by `Display.scaleFactor`
(queried live via `screen_retriever`, itself confirmed to genuinely compute this via
`FlutterDesktopGetDpiForMonitor`, not a stub). A further few-pixel residual (likely DWM's own
invisible border/shadow around a borderless window) was tuned by hand against the real screen
rather than reasoned about further — landed at `-5` logical px, adjusted directly by you after
`-2` still showed a hair of a gap.

**Window sizing was a second, separate bug**, found on the very next screenshot: the app was
still leaving the whole right edge of the screen unused. Cause: `main.dart` restored a previous
manual resize's *size* even though position was already being freshly computed — an old saved
width (from before scrcpy was ever part of the picture) simply wasn't wide enough to reach the
screen's edge. Given the ask ("make sure this space is actually taken by our app when it starts")
is explicitly about *every* launch behaving identically, the whole `WindowGeometry`
save/restore mechanism was removed rather than partially preserved — a persisted preference
that's designed to always be overridden by a fresh computation isn't worth the complexity of
keeping around half-used. `core/window_geometry.dart` deleted.

**A third bug, found by you clicking "Classify" several times while Scrape was actively
running and seeing nothing happen:** `LivePage`'s postFrameCallback (a one-time "catch up on
data that arrived before this page mounted" nudge) was actually re-firing on *every* rebuild —
including the rebuild caused by the manual click itself, since `selectedFlowProvider` is one of
`LivePage`'s own `ref.watch`ed dependencies. Each click's own rebuild immediately re-ran
`_maybeAutoSelect`, saw Scrape still running, and silently re-selected it back within the same
frame — a real bug, not the "auto-follow overrides a stale click" behavior chosen in D67, since
here the override was firing off the click's *own* rebuild rather than any genuine new scheduler
data. Fixed with a `_didInitialCatchUp` flag so the postFrameCallback only ever fires once; all
subsequent auto-follow behavior now comes exclusively from `ref.listen`'s reaction to *real*
`flows.state` broadcasts, which still correctly overrides a manual click the moment something
actually changes.

**A fourth item was a design revert, not a bug:** the Scan surface's newest-at-top,
no-scroll-needed ordering (D67) had been copied onto Classify too, unintentionally — you'd only
asked for the "one entry per row, no wasted space" layout change there, not the ordering change.
Classify reverted to its original oldest-at-top / auto-scroll-to-the-newest-at-the-bottom pattern,
keeping D67's layout fix (full-width image, caption below).

**New feature: a Stop button**, requested directly out of the D68 incident below — there was
genuinely no way to halt a run already in progress from the control center short of uninstalling
the whole Helm release. New `prefect.cancel_flow_run()` (agent) sets a flow run to `CANCELLING`
via Prefect's REST API — the same transition the Prefect UI's own Cancel button triggers — exposed
as `POST /api/flow-runs/{id}/cancel`. `forceRunFlow`'s confirmation-dialog pattern was extracted
into a new shared `core/force_run.dart` (deduplicating what used to be a private copy inside
`FlowCard`) alongside a new `stopFlowRun`, and both now appear on the Flows screen's cards and the
Live screen's header, visible only while that flow's `phase == 'running'`.

**Verified:** `flutter analyze` clean, `flutter test` 39/39 across every round in this section. Agent:
all 13 suites green (475 checks) after the new cancel endpoint; `test_flowruns.py` unaffected.
Built and started for you between every round, live-retested by you each time — the window
position/sizing, the Classify-click bug, and the Stop button were all confirmed fixed live in this
same session.

### D68 · A same-session regression: the disabled-profile guard (D64) was silently skipping every real profile, PRIVATE or PUBLIC — a real production incident

**What happened:** once D64/D66/D67's Insta-Automate changes were redeployed and you resumed
testing for real, every single profile `entity_scrape` touched was logged and skipped as
`"UNAVAILABLE"` — including profiles you could see, live on the mirrored phone, rendering
completely normally (a real, existing, PRIVATE Instagram profile with its own private-account
banner visible). This wasn't a rare edge case; it broke scraping outright, for every profile, and
you had to **uninstall the `insta-automate` Helm release** to stop it — the harshest stop
available, used precisely because D69's Stop button didn't exist yet.

**Root cause:** D64's guard checked only `ui.profile_tabs_container.wait(timeout=5)` — a
PUBLIC-profile-only signal (`controllers/device.py`'s own `_profile_entity_access` uses it
exactly that way, `elif self.ui.profile_tabs_container.exists: return EntityAccess.PUBLIC`). A
legitimate PRIVATE profile never has that element either — it shows a lock/banner instead — and
PRIVATE is **scrape's own dominant, expected case**: the very next check in the same function,
`if user.access == EntityAccess.PUBLIC: skip`, exists precisely because scrape only wants PRIVATE
profiles. D64's guard was checking the wrong half of a two-sided condition, so it treated the
majority of real, working input as if it were the rare disabled-page case it was written for.

**Fixed by reusing `IaDevice._profile_entity_access()` directly** (already implements the correct
three-way PRIVATE/PUBLIC/neither check) instead of re-deriving a partial version of the same
logic — called once, early, with its result carried forward into `User.access` rather than
re-querying it a second time later in the function (which the pre-D64 code did, at the default
30s timeout). `None` (neither signal ever appears) is the only case that still means genuinely
unavailable.

**The verification gap that let this ship:** D64's own throwaway script never modeled the
private-banner case at all — its `FakeUI` had only `profile_id`/`profile_tabs_container`, so it
was structurally incapable of catching this regardless of how many cases it ran. The corrected
script explicitly exercises all three real outcomes of `_profile_entity_access` (PRIVATE must
proceed unskipped, PUBLIC must proceed unskipped by *this* guard then get skipped by the
pre-existing separate check, `None` must skip as `UNAVAILABLE` without ever reaching
`User.from_ui`) — 6/6 passing this time actually means something.

**Recovery, in order:** committed + pushed the fix, `GIT_BRANCH=feat/control-center ia build`,
`helm install insta-automate` (the release you'd removed — chart's `values.yaml` needed no
changes), restored the two manual `kubectl set env` patches (`IA_AGENT_TOKEN` on both
deployments, `GIT_BRANCH` on the scheduler — neither is in the committed Helm chart, so a
reinstall from scratch loses them, not just a restart) and `GIT_BRANCH=feat/control-center ia
prefect deploy` again (the worker's `create-work-pool` init container recreates the pool on every
pod start, D38's already-documented behavior). Verified live: both pods' installed source
confirmed via `kubectl exec` to have the fix, env vars intact, scheduler reporting `online: true`
with every flow gating normally. **Not yet re-confirmed against a real scrape run** — the
recovery was verified structurally (code present, pods healthy, gates sane) but no profile was
actually scraped again in this session to watch it succeed end to end.

### D67 · Ingest/Scan/Classify surfaces redesigned from a second round of live feedback; the Live screen's stale-flow-content bug found and fixed

**Ingest never had the image it was trying to show.** `IngestSurface` assumed `entities/<id>.jpg`
(the event's own `image` field) would usually exist — it doesn't, ever, at ingest time:
`export_entity()` (the only code that writes that file) is called from `scan_entity_init`, a
*later* flow, not from `add_new_entity` itself. Every ingest card was rendering a permanent
"image unavailable" placeholder that read as broken. Rather than build a new screenshot-capture
pipeline change (scoped and explicitly deferred — a real feature addition needing live phone
testing, not a bug fix), `IngestSurface` was rebuilt as a metadata card: a type-based icon,
the entity id, its URL, and type/access badges — all already present in `entity.added`'s own
`extra` field, no pipeline change needed.

**Scan's ordering, corrected again from your own clarification:** the vertical layout (D62) still
auto-scrolled to the bottom on new items — you'd actually meant the newest item to render
pinned at the top with nothing older ever needing to be scrolled to see it, closer to a
live activity feed than a chat log. Re-implemented without `reverse: true` (that flag is
specifically the chat-message "newest anchored at the bottom" pattern, not what was wanted here) —
newest-first is now just the first item in a plain top-down `ListView`. Also switched from two
images per row (an unintended side effect of `Wrap` at this pane's width) to one full-width image
with its caption below, matching what "one entry per row" actually meant.

**A real, separate `LiveController` bug:** switching flows (Ingest → Scan, auto-followed) left the
log console and visualization surface showing Ingest's *stale* content under the Scan tab for
several seconds, self-correcting only once you manually navigated away and back. Cause:
`AsyncNotifier`'s default `skipLoadingOnRefresh` behavior keeps showing the previous value while
a dependency-triggered rebuild is still in flight — exactly what a widget watching
`liveControllerProvider` with a plain `.when(loading: ...)` sees. Fixed by explicitly forcing
`state = const AsyncValue.loading()` at the top of `build()` whenever the *flow itself* changed
(not just its logs/events), so a real flow switch always shows a genuine loading state instead of
another flow's leftover data.

**New: a Force Run button on the Live screen's header** (your own request — "convenient to not
have to switch tabs just to trigger a flow and watch its logs"), working on whichever flow is
currently selected, reusing `FlowCard`'s existing confirmation-dialog logic (now shared, see D69).

**Verified:** `flutter analyze` clean, `flutter test` 39/39. Confirmed live: Ingest → Scan → Scan →
Classify all auto-followed correctly in your retest (this is what first surfaced D66's still-open
gap, addressed separately below).

### D66 · Message-triggered ingest never surfaced as `phase: "running"` in the scheduler snapshot

Root cause, found from your own retest: `entity_ingest_message_trigger` (the Telethon `NewMessage`
handler that fires instantly on a channel post — the "real-time" ingest path ARCHITECTURE
describes) calls `entity_ingest_trigger()` directly, bypassing `entity_ingest_time_trigger()`'s
loop entirely — the *only* place that calls `self._set_state("entity-ingest", phase="running",
...)`. The flow itself ran correctly; the scheduler snapshot simply never reflected it, so nothing
reading `phase` (the Live screen's auto-follow, in particular) could tell it was happening. Fixed
by setting `phase="running"` (then back to `"idle"` on completion) directly inside the message
handler too, tagged with `_current_flow.set("entity-ingest")` for D63's log-routing to pick up
correctly as well.

---

## 2026-08-02 — Seven bugs from live use, fixed in one session: real research first, then real redeploys

You listed seven things wrong with the app from actually using it (two screenshots included).
Three parallel Explore agents root-caused all seven before any code was touched — worth recording
because two of the seven turned out not to be what they looked like at a glance: the "Follow
button" cards in the Scan screenshot were native Instagram row-crop screenshots, not an app bug,
and the notification code was already correct — the real problem was D59's own flagged loose end
(never independently confirmed against a real Telegram delivery).

### D65 · scrcpy's `--adb=` flag doesn't exist — D55's fix silently failed every launch since the day it landed

**The report:** screen mirroring stopped working after D55's adb-churn fix, which the user
correctly suspected was related rather than coincidental.

**First finding: the fix's own mechanism was still intact but fragile.** `wsl-bridge`'s
`pyproject.toml` had no `rev`/`branch` pin on `my-modules` at all — its `uv.lock` was resolved to a
commit from *before* D55's fix, a live-venv hotfix one `uv sync` away from silently reverting.
Fixed by pinning `my-modules = { git = "...", rev = "<commit>" }` explicitly rather than trusting
the unpinned default to keep resolving to the right thing — the same durable-pin-over-live-hotfix
upgrade D55 itself deferred ("pending a real release").

**Second, bigger finding, only surfaced by actually starting a real mirror and reading the
process list: D55's fix never worked at all.** `scrcpy 3.3.4` has no `--adb=<path>` CLI flag —
running the exact command `my_modules.scrcpy.Scrcpy.start()` builds gets `scrcpy: unknown option
-- adb=...`, invisible in production because the class's own `Popen(..., stdout=DEVNULL,
stderr=DEVNULL)` swallows it. scrcpy only exposes this via the `ADB` **environment variable**
(confirmed against `scrcpy --help`'s own "Environment variables" section). D55's commit shipped
without ever launching a real mirror to confirm it worked — the churn-fix half (adb server binding
to `0.0.0.0`) was real and tested; this half wasn't. Fixed with a new commit on the same
`fix/scrcpy-adb-version-pin` branch (`94b308a`, still unmerged): `env["ADB"] = ADB` passed to
`Popen`, flag removed. Manually verified the raw command against a real error message before
writing the fix, then re-verified the corrected version against the real phone — mirror launches,
positions correctly (`snapped: true`, previously `false`), and is trackable through
`/api/device` for the first time since D55.

**Also found and fixed: a live orphaned mirror.** A `scrcpy.exe` process was running with no flags
at all — not launched through wsl-bridge's own `/scrcpy/start`, using the wrong bundled adb,
invisible to `GET /scrcpy/`. Killed with the user's confirmation first (a real on-screen window).

**Verified end to end:** stop wsl-bridge (agent-supervised) → `uv sync` → start via the agent →
`POST /api/device/scrcpy/start` → `snapped: true`, `/api/device` reports `mirroring: true` →
`POST /api/device/scrcpy/stop` → confirmed zero `scrcpy.exe` processes remain. This is the first
session this mirror has been proven to actually work end to end since CP 4.5.

### D64 · Disabled/unavailable Instagram profiles now skip gracefully instead of crashing `entity_scrape`

`profile_scrape` (`tasks/ia.py`) called `User.from_ui()` unconditionally once a profile page's app
bar populated — but a disabled/unavailable account still shows a username in the app bar while
having none of the post/follower/following elements `User.from_ui` reads without an `.exists`
guard (unlike `name`/`bio`, two lines above it, which already have one). Uncaught, this burned all
3 of `@ia_task()`'s retries (~90s) then hard-failed the whole `entity_scrape` run, aborting every
other queued profile in it too — a single bad profile in the queue could silently stop a run that
had nothing else wrong with it.

No live disabled profile was available to inspect Instagram's actual "account unavailable" page
copy/resource-ids, so rather than guess a new selector, the fix reuses the existing, already-proven
`profile_tabs_container` (`controllers/device.py`, already used by `_profile_entity_access` to mean
"this is a normal loaded profile") as a pre-check before `User.from_ui()` runs — a missing element
now short-circuits into the same `scrape.skipped(reason=...)` event pattern already used for
PUBLIC/NO_POSTS/FMIN/FMAX, rather than raising. **Flagged as best-effort**: verified by a throwaway
script (`.fn()`-level, every dependency faked) proving both branches — a missing
`profile_tabs_container` skips cleanly with `reason: "UNAVAILABLE"` and never reaches
`User.from_ui`, a present one falls through unaffected — but never exercised against a genuine
disabled account, since none was in the queue this session.

### D63 · Scheduler-pod log lines are now tagged by flow at the source, not broadcast to every active run

The Live screen's log pane showed other flows' trigger/gate lines mixed into whichever flow was
selected (`agent/flowruns.py`'s `_poll_scheduler_pod` sent every scheduler-pod line into *every*
currently-active run's ring — never attempted per-flow filtering at all), plus a duplicated
timestamp/level (`my_modules.logger`'s `RichHandler` already renders `[date] time LEVEL ... file:
line` into the raw text, and the app's `LogConsole` renders its own pill in front of that same
text).

Chose the real fix over an agent-only text-matching heuristic (checked with the user first) because
a heuristic provably misattributes real lines — Classify's own "Scanned entities found to classify"
gate-check line mentions "classify" but is Classify's own log, not Scan's; text content isn't a
reliable signal for *who logged it*, only a `contextvars.ContextVar` set once per trigger-loop task
is. `controllers/prefect.py` gained `_current_flow` + a `logging.Filter` that prefixes every record
from within a loop's task context with `[entity-scan]` etc. — one `_current_flow.set(...)` line per
trigger loop, no changes needed to individual `log.info`/`log.error` call sites or to `Deployment`,
since asyncio tasks each carry their own copy of the contextvar. `flowruns.py::_poll_scheduler_pod`
was rewritten to reconstruct Rich's wrapped multi-line records (a known, previously-unhandled gap
its own docstring already flagged), strip the baked-in prefix/suffix, route by the extracted tag to
only that flow's active run(s), and drop untagged lines (the startup banner, telegram-keepalive)
rather than broadcasting them — there's no consumer for a flow-agnostic scheduler stream today.

**Verified:** `agent/tests/test_flowruns.py` grew from 34/36 (2 pre-existing checks failed
immediately after the rewrite — correctly, since the old fixture's untagged lines are now
correctly dropped) to 39/39 after updating the fixture to the real tagged/wrapped shape and adding
checks for cross-flow isolation and wrap-reconstruction. All 13 agent suites green (698+ checks).
Bundled into one `Insta-Automate` commit with D64 and one redeploy cycle, deliberately, to avoid
two separate live pod restarts for two related fixes in the same session.

### D62 · Scan filmstrip changed from horizontal to vertical

`scan_surface.dart`'s row-crop images (1080:198 — wide, short) scrolled left-to-right in a fixed
180px-wide `ListView.separated(scrollDirection: Axis.horizontal)`. D44 had called this "not a
problem" for a different concern (cards not using pane width) and never actually evaluated
direction against what the user wanted — this session's explicit feedback overrides that. Converted
to the same vertical `SingleChildScrollView` + `Wrap` + scroll-to-`maxScrollExtent`-on-new-item
pattern already proven in `classify_surface.dart`, rather than inventing a new one.

### D61 · Live screen's auto-follow-the-running-flow only ever fired once, not "only for Scrape"

`live_page.dart`'s `_autoSelected` was a one-shot latch, not a per-transition flag — the first flow
observed `running` (usually Scrape, the shortest cycle) set it `true` permanently, silently
disabling auto-select for every later flow change for the rest of the session. Nothing was actually
scrape-specific anywhere in the surrounding code; the symptom was just "whichever flow happened to
run first, forever." Fixed by renaming the flag to mean only "the user manually picked a tab"
(`_userSelected`, set solely in the chip's `onSelected`) and re-checking whether the *currently
selected* flow is still running before ever considering an auto-switch — so the view now follows
every flow transition, not just the first one, until a real manual click opts out.

### D60 · Bugs 1 & 5 (Telegram fallback / missing hyperlink) were D59's own flagged loose end, not new bugs — closed for real this time

Investigation confirmed all of D59's four code paths were already correct (`notify()`'s fallback
logic, `EventBus`'s device-tagging, all three per-profile call sites' `url=`/`always_telegram=True`)
— D59 itself had already written "not yet independently confirmed: a real Telegram delivery
post-fix." This session did that confirmation for real: `kubectl exec`-ed into both pods and
grep-confirmed the D58/D59 code was genuinely loaded (it was — the pods hadn't gone stale again),
then called `notify()` directly inside the worker pod with zero paired devices connected. Result:
`delivered=False` (correctly reflecting zero real phone connections) → fell through to Telegram →
**user confirmed the message actually arrived.** The historical "Scan complete" entries with
`url: null` visible in `GET /api/notify`'s replay are pre-D58/D59 history sent by the stale pod
D59 already documented, not a live recurrence — every entry after this session's redeploy carries
`url` correctly.

Landed as part of the same commit + redeploy cycle as D63/D64, plus this session's own two additional
Insta-Automate fixes — `GIT_BRANCH=feat/control-center` was set explicitly for **both** `ia build`
and `ia prefect deploy` this time (the user flagged, correctly, that `ia build` needed the same
discipline `ia prefect deploy` already required after D55/D59 — `ia build` in fact resolves the
branch from the locally checked-out branch via `git branch --show-current`, not `GIT_BRANCH`, but
setting it explicitly regardless is the safer standing habit and was verified either way: the
generated Dockerfile's `pip install git+...@feat/control-center` was checked against the exact
commit hash before trusting it).

---

## 2026-08-02 — D58's pipeline half never reached the live worker pod; found from your own report

### D59 · A forgotten `git push` meant the worker pod kept skipping Telegram — same undeployed-code shape as D36/D39, different specific cause

**The report:** you noticed the three "always Telegram" notifications had stopped arriving on
Telegram, despite D58 landing that exact behavior hours earlier.

**Root cause, confirmed before touching anything:** D58's `Insta-Automate` commit
(`3e2186a`, `feat/control-center`) was created with `git commit` but never `git push`ed — the
worker pod's Prefect deployments `git_clone` from GitHub, not local disk, so it was still running
the pre-D58 `notify()` with no `always_telegram`/`url` at all (confirmed by `kubectl exec`-ing in
and reading the installed source directly, same technique as D39). Combined with the *agent* half
of D58 — already live, since `ia-agent.exe` is a local process I'd already restarted — correctly
computing `delivered` from real phone connectivity instead of "any WS client, desktop included,"
the live pipeline now saw `delivered=True` almost continuously (your phone's foreground service
holds a connection open most of the time) with no `always_telegram` override yet deployed to force
Telegram anyway. Every notification, not just the three per-profile ones, had been silently
skipping Telegram whenever your phone was connected — this is D53's original risk, made worse by
the agent-side fix landing before the pipeline-side override that was supposed to compensate for
it in the one case (per-profile notifications) where losing Telegram matters most.

**Fixed the same way as D39: push, `ia build`, restart, `ia prefect deploy`.** `git push origin
feat/control-center`, `ia build` (pinned the new commit, confirmed via the build log), `kubectl
rollout restart deployment/insta-automate-worker`, then verified the *new* pod's installed
`notify()` actually has `always_telegram`/`url` before doing anything else. The restart re-hit
D38's known work-pool-orphaning init container as expected — fixed the documented way,
`GIT_BRANCH=feat/control-center ia prefect deploy` (D55's exact lesson: a bare local shell
defaults to `main` without it). All 5 real flows + `sample-flow` confirmed `READY` against
`insta-automate-pool` afterward, and the scheduler's live state showed no crashes, normal gate
reasons across the board.

**Not yet independently confirmed:** a real Telegram delivery post-fix — there's no way to force
one without waiting for a genuine per-profile event (a follow, an already-known entity, an
unfollow-prompt) or a general notification while the phone happens to be connected. Flagged for
whoever picks this back up to watch for.

**The durable lesson, worth restating since this is at least the third time this exact shape has
bitten a session (D36, D39, now D59):** a local `git commit` is not deployed. Every checkpoint that
touches `Insta-Automate` needs an explicit "did I push, and does the live pod actually have this"
check before calling the work done — D58's own write-up asserted verification without that check,
which is exactly how this slipped through for hours undetected.

---

## 2026-08-02 — CP 6.4 built, then a notification redesign found by actually using it

### D58 · Device-aware notify routing, plus per-profile notifications get a real tap target and clean text — spans all four repos

CP 6.4 (mobile client) shipped all four planned slices (pairing, WS + foreground-service push
notifications, compact live flow view, config write-through) and each was verified live against
the real agent and a real phone — see the session's build log. Using it for real (both the
desktop's notification bell and the new phone notifications) surfaced three problems serious
enough to fix before calling the notifications phase done, per your explicit instruction:

**1. Markdown showed as raw text.** `**[@user](url)**`-shaped messages are built for Telegram's
renderer, but the same string is stored/shown verbatim by the agent — the desktop's notification
center displayed the literal asterisks and brackets.

**2. Routing was actually wrong, not just imprecise — this is D53's deferred risk, now real.**
`NOTIFY_POLICY=app_first`'s `delivered` meant "at least one live WS subscriber," which included
the *desktop app itself*. Once a phone client existed, having the desktop open at all would
silently swallow every notification that should have gone to Telegram. Fixed at the source:
`EventBus` (`agent/src/ia_agent/events/bus.py`) now tags every subscriber with the device id that
authenticated it (`None` for desktop), `subscriber_count(devices_only=True)` counts only phones,
and `NotificationStore.publish()` uses that count for `targets`/`delivered`. `ws.py` computes the
device id by calling `pairing_store.authenticate(credential)` a second time after the existing
`is_authorized()` check (harmless for desktop — no device token matches it). `EventBus.publish()`
itself is unchanged — the desktop still receives everything; it's a passive viewer that never
gates delivery or blocks Telegram either way. Small bonus riding the same plumbing: `GET
/api/pair/devices` now reports a live `connected` bool per device (cross-referencing
`EventBus.device_ids()`), not just `last_seen` — real confirmation of "actively connected," which
is the exact distinction you drew a line under ("don't confuse with simple pair").

**3. Three notifications are about one specific profile, not a flow-level event** — found by
auditing every `notify()` call site in `Insta-Automate`: `notify_profile_unfollow` ("scan
complete, you can unfollow"), `profile_follow`'s followed-by branch ("X is followed by Y"), and
`add_new_entity`'s already-exists branch (the third one, not in your original two — confirmed with
you before including it). These get two things the other seven call sites don't: a new
`always_telegram=True` param on `notify()` (independent of `NOTIFY_POLICY`) that forces Telegram
delivery regardless of whether a phone is connected, since these are judged consequential enough
to always leave a Telegram record; and a `url` field (the `Entity.url` already in scope at each
call site — no extra lookup needed) that flows agent-ward as the notification's tap target on
both clients, rather than relying on an inline clickable link inside possibly-truncated text.

**Rendering approach — deliberately not a markdown package on either client.** Both apps already
prefer small hand-rolled parsing for narrow needs (desktop's `FileOpener` instead of
`url_launcher`, e.g.) — new `core/notification_text.dart` (desktop) and its mobile twin
(`notification_text.dart` in `Insta-Automate-Client`) both strip `[text](url)` down to `text` and
drop `**` entirely rather than rendering it bold; the link itself is dropped from display
regardless since navigation is now the whole tile's job via the `url` field, not a fragile
inline-span tap target inside a 3-line ellipsized `Text`. **First version bolded the stripped
text on desktop — corrected from your live feedback**: plain text reads better here, so desktop's
formatter was simplified to exactly match mobile's (same function, same output shape), dropping
the now-unused bold-`TextSpan` machinery entirely. Mobile's tap-to-open is wired through a second
`FlutterLocalNotificationsPlugin` instance in the main isolate (tapping a notification is
inherently a main-isolate/UI event regardless of which isolate posted it), reusing the app's
existing `url_launcher` dependency and exact launch convention already used everywhere else in
that app (`queue_entity_card.dart` etc.).

**Also from your live feedback: the "followed by" name needed a leading `@` for visual
consistency with the linked profile above it**, even though it's not itself a link. Fixed at the
pipeline source (`tasks/ia.py`'s `profile_follow`), not the client formatters, since it's message
*content* — a regex inserts `@` right after Instagram's own `"Followed by "` UI text
(`ui.followed_by.get_text()`), before whatever name(s) follow. On Instagram's own multi-name
phrasing ("Followed by X and 3 others") only the first name gets the `@`, accepted as a minor
edge case since this is cosmetic polish, not a second link target.

**Verified:** agent — `agent/tests/test_notifications.py` grew to 37/37 (new cases distinguish a
desktop-only subscriber from a device one, and prove the desktop still receives the broadcast
despite `delivered=false` — the actual regression test for the bug), `test_pairing.py` to 31/31
(the new `connected` field flips true/false around the WS lifecycle); the full 13-suite agent
regression (698 checks total) stayed green. One real mistake caught before it stuck: the first
version of the `test_notifications.py` pairing addition didn't scratch-redirect
`PAIRING_DEVICES_PATH` like `test_pairing.py` already does, so it briefly wrote a fake "test
phone" into the *real* `%LOCALAPPDATA%\ia-agent\pairing.json` — caught immediately, fixed, and the
real file cleaned back up by hand. Live-checked against the real agent + your actually-connected
phone afterward: `GET /api/pair/devices` showed `connected: true` only for the live phone,
`POST /api/notify` reported `delivered: true` with it connected.

Pipeline — no test suite (standing precedent since CP 3.1); import sanity-check across every
changed module, plus a throwaway script (8/8) exercising all four `notify()` combinations
(device-active/inactive × general/`always_telegram`) against a monkeypatched `AgentClient`/
`IaTelegram`, confirming exactly which channel(s) fire in each case. Nothing deployed to the live
pod — same standing precedent as every `Insta-Automate` checkpoint since CP 4.3.

Desktop — `flutter analyze` clean, `flutter test` 39/39 (38 prior + 1 new: a per-profile
notification with markdown and a long username renders without overflow, the raw `**[`/`](https`
syntax never appears literally, and the open-link icon shows). Built and started for you per
rule 5 — confirmed live by you, twice: once against the original bold rendering (which prompted
the plain-text correction above) and again after the fix plus the `@`-prefix change, both times
against a real notification posted through the real agent.

Mobile — `flutter analyze` clean (no test suite exists for this app, matching CP 6.4's own
precedent that real verification here is on-device, not unit tests). Built, installed on the
connected test phone, and confirmed live against the real agent: a real per-profile-shaped
notification (`**[@user](url)**` message, `url` field set) arrived with clean readable text and
no raw markdown, and — per your report — worked end to end.

---

## 2026-08-02 — Session resume: CP 6.3 status reconciled, CP 6.4 ground rules set

### D57 · CP 6.3's "not committed yet" note was stale relative to the actual commit; CP 6.4 ground rules confirmed before writing any code

**The docs and the repo had drifted.** `CLAUDE.md` and `DECISIONS.md` (D56, below) both still read
"awaiting your test" / "not yet committed, per rule 4" even though commit `b2dd16b` — the same
commit that carried that text — was already on `main` with a message describing real verification.
Resolved by asking the user directly rather than guessing which side was right. Answer: the
verification described in the commit message did happen (pairing + notification bell against the
real agent), but it doesn't make CP 6.3 *fully* tested — that requires the phone side, which was
backend-mocked with `curl` standing in for `/api/pair/claim` because CP 6.4 (the actual mobile
client) doesn't exist yet. `CLAUDE.md` corrected to say exactly that instead of either extreme.

**CP 6.4 ground rules, confirmed before any code:**
- Work happens in `flutter/Insta-Automate-Client` (pubspec `ia_manager`) on `feat/lan-agent` only
  — never `main` — per rule 3, re-confirmed rather than assumed.
- After each change, build a real APK and install it on the phone currently connected over adb;
  that's the test loop for this checkpoint, not `flutter test`/`flutter analyze` alone (those
  still run, but an Android foreground-service WebSocket and real notification delivery need a
  real device).
- Any step needing a human — accepting an install prompt, granting a permission, actually scanning
  the QR — stops and asks rather than being scripted around.
- **The adb-connected test phone is not the user's production phone.** Its `IA_DIR` is stale, with
  no active Syncthing sync to this laptop — it's a coding/testing device only. The user's own,
  separate phone is the one with real `IA_DIR` sync, and CP 6.4 is not tested against it. A test
  result like "no images render" on the test phone may just mean stale local data, not an app bug
  — check which is which before treating it as a regression.

---

## 2026-08-02 — Phase 6 implementation session (CP 6.3, Desktop pairing & notification center)

### D56 · Built on D54's placement decision with no new agent code; a real header-row overflow was caught by the new layout test, not by `flutter analyze`

**CP 6.3 needed no agent-side changes at all** — CP 6.1 already shipped the full REST surface
(`/api/pair/*`, `/api/notify*`) and the `notifications` WS channel; this checkpoint is purely the
Flutter client on top of it. New `app/lib/features/settings/devices_controller.dart` +
`devices_tab.dart` (the "Devices" Settings tab D54 placed pairing in) and
`app/lib/features/notifications/notification_controller.dart` + `notification_center.dart` (the
title-bar bell). `core/pairing_models.dart` and `core/notification_models.dart` mirror the
agent's JSON shapes; `core/relative_time.dart` is a small shared "3m ago" formatter for both the
paired-device list's last-seen and the notification center's timestamps.

**QR payload is exactly `iacc://pair?h=<lan-ip>&p=8787&c=<code>`, per ARCHITECTURE §7** — no new
format decision needed, `qr_flutter` (already the planned dependency per §9) renders it directly
from `PairingCode.qrPayload`. The pairing card has no dedicated Riverpod controller beyond
`DevicesController` (start/list/revoke) — the mint→countdown→poll-for-claim→celebrate state
machine is local `StatefulWidget` state (`_PairingPhase`), since none of it is data anything else
on screen needs; polling for a claim is a 2s timer diffing device ids against a snapshot taken at
mint time, because CP 6.1 never wired a WS channel for pairing (a claim happens on the *phone*,
so the desktop has nothing to subscribe to — this was already flagged as a known gap in CP 6.1's
own notes).

**Per-tag mute is client-side only, persisted via `shared_preferences`** (the same store
`WindowGeometry` already uses) — there is no server-side "muted" concept, since `NOTIFY_POLICY`
already governs desktop-vs-Telegram routing (§6) and this is purely "don't show me this category
in the center." `unreadNotificationCountProvider` (the bell's badge count) excludes muted tags so
a muted category stops drawing attention to itself, matching what "mute" should mean.

**Found by the new `notification_center_layout_test.dart`, not `flutter analyze` (D19's
precedent, again):** the panel's header row (`Text('Notifications')` + `Spacer()` + filter
`IconButton` + "Mark all read" `TextButton`) overflowed by a consistent 101px regardless of window
size or notification content — reproducing on both the long-message test and the all-muted-empty
test, which share nothing but that header. Fixed by wrapping the title in `Expanded` +
`TextOverflow.ellipsis` instead of `Spacer()`, so the flexible title always yields space to the
fixed-size trailing controls rather than the row ever demanding more width than it's given.

**Also worth knowing for whoever touches this test file next:** `CompositedTransformFollower`'s
global position resolves at paint/composite time, which `flutter_test`'s hit-test-based tap
warning doesn't always account for on the frame right after an `OverlayEntry` is inserted —
tapping the bell and the panel's own filter icon both print a benign "would not hit test" warning
even though the tap genuinely lands (confirmed by asserting the `FilterChip`s the tap was
supposed to reveal actually appear). `warnIfMissed: false` is used at both call sites for that
reason, not to paper over a real mis-tap.

**Verified:** `flutter analyze` clean, `flutter test` 38/38 (26 prior + 12 new across
`devices_layout_test.dart` and `notification_center_layout_test.dart` — a 52-char paired device
name, the QR/code panel at the app's 1024px minimum window, a 400-char notification message with
no spaces, a long tag name in the filter row, and the all-tags-muted empty state). `flutter build
windows --debug` succeeds. **Not yet user-verified** — per rule 5, Claude built, analyzed, and
started the freshly built exe for you to test against the real running agent (real pairing round
trip with a phone once CP 6.4 exists, or manual-code entry for now; revoke; the notification
center against whatever `POST /api/notify` traffic the now-live CP 6.2 facade produces) — this
checkpoint is not committed yet, per rule 4.

---

## 2026-08-02 — Live incident: FOLLOW frozen "running" for hours, five things found chained together

### D55 · An uncaught adb exception froze `entity-follow`'s trigger loop forever; chasing why led to four more real, chained bugs

**The report:** the Flows screen showed `entity-follow` stuck at "running" for many minutes with zero flow runs triggered, despite 191 real files sitting in `follow_queued/`.

**Root cause #1 — the actual freeze.** `entity_follow_trigger()` (`controllers/prefect.py`) sets `phase="running"` then calls `wait_for_device()`, whose polling loop (`tasks/device.py`) had no exception handling around `IaDevice.connected()`. A transient adb connection refusal raised `AdbConnectionError` straight out of the loop, which killed the whole `asyncio.create_task()`-launched trigger loop permanently and silently (`Task exception was never retrieved` — never surfaced anywhere). The frozen `phase="running"` was simply the last state written before the task died; `heartbeat_loop()` kept re-broadcasting it forever since nothing was left to update it. Confirmed via Prefect's API: literally zero `entity-follow` flow runs since the scheduler pod's last restart, and the pod's own logs never printed another `entity-follow` line after that traceback.

**Fix:** all five trigger loops plus `keep_telegram_alive` wrapped in try/except (log, set a visible `"error"` gate, retry after one `TICK`) — general resilience, not just entity-follow. More importantly, `wait_for_device()` itself now treats a raised exception from `IaDevice.connected()` the same as "not connected yet" rather than propagating, fixing every caller (including `serve()`'s own unguarded startup call) at the source.

**Root cause #2 — why adb was refusing connections at all, found deploying the fix.** The host's currently-running adb server was bound to `127.0.0.1` only — not `0.0.0.0` — making it *unreachable from any pod, always*, not intermittently. The agent's own supervised adb command includes `-a` (all interfaces), but the live process was `origin: external`, started by something else without `-a`. Root: scrcpy's Windows build prefers an `adb.exe` sitting next to `scrcpy.exe` over PATH; the winget-installed scrcpy's bundled copy (v36.0.0) differs from the one actually running the server (v36.0.2, from `platform-tools`/PATH). adb's version-mismatch behavior kills and restarts the server on every scrcpy launch — and `device.start_scrcpy()` fires on every successful `wait_for_device()`, so once retries were made resilient (the fix above), *every* brief reconnect immediately re-triggered scrcpy, which killed the connection again in a tight ~30-45s cycle. This is the same pattern you'd already noticed in Services ("Take over" holding only "a minute or so" before reverting to `external`).

**Fix:** `my_modules.scrcpy.Scrcpy.start()` now passes `--adb=<path>`, pinned to whatever `shutil.which("adb")` resolves (the same binary the agent's own service spec already treats as canonical) — stops scrcpy from ever reaching for its mismatched bundled copy. Committed to `my-modules` on a new branch (`fix/scrcpy-adb-version-pin`), **not merged to main** (repo hygiene, same as every other cross-repo change). Made live immediately with a direct hotfix — copying the fixed file into `wsl-bridge`'s already-installed venv copy and restarting the (agent-supervised) `wsl-bridge` service — since `wsl-bridge` pins `my-modules` via an unpinned git dependency and a proper release wasn't warranted mid-incident. **This bypasses the normal git-dependency pipeline; a future `uv sync` in `wsl-bridge` will silently revert it** until `fix/scrcpy-adb-version-pin` is actually released and `wsl-bridge`'s lockfile updated. Flagged here so it isn't forgotten.

**Root cause #3 — deploying the scheduler fix nearly caused a worse outage.** Rebuilding and restarting the scheduler pod (`ia build` + `kubectl rollout restart`) hit the live version-mismatch churn described above at the worst possible moment: `serve()`'s own top-level `wait_for_device()` call (pre-fix, unguarded) raised on every single pod startup attempt for several minutes, producing a genuine `CrashLoopBackOff` — the entire scheduler down (all five flows), not just Follow. **Learned live: `ia build` re-tags the same image name every time (`insta-automate:3.6.27-python3.12`, no digest/commit suffix), so `kubectl rollout undo` does not actually restore the previous code** — the "old" ReplicaSet's pod spec references the same tag string, which the node's local image cache had already overwritten. Rolling back was a no-op in practice; only actually fixing `wait_for_device()` (root cause #1's real fix) stopped the crash loop. Worth remembering next time a rollback is reached for after `ia build`.

**Root cause #4 — the worker pod was 6+ checkpoints stale.** Once the scheduler recovered, `entity-follow` finally created a real flow run — which crashed instantly with `ModuleNotFoundError: insta_automate.controllers.notify`. CP 6.2 (the notifier facade, committed and pushed to `feat/control-center` days ago) was, per its own checkpoint notes, deliberately never deployed to the live worker pod. `git_clone`'s pull step only refreshes the flow's own top-level file, not what it imports (D39's exact precedent) — the worker's baked Docker image predated CP 6.2 entirely. **Decided with you mid-incident, not assumed:** restarting the worker now deploys CP 6.2 to production for the first time, earlier than the original "wait until the whole control center is accepted" plan (rule 3) — you approved it explicitly since it's what's actually needed for Follow (and anything downstream of `notify()`) to run at all. Restarting re-triggered D38's already-documented work-pool-orphaning init container; fixed the same documented way (`ia prefect deploy`).

**Root cause #5 — found only while fixing #4: `ia prefect deploy` run from a bare local shell silently deploys from `main`, not the feature branch.** `IaFlows.deploy_all()` builds each deployment's `parameter_openapi_schema` by cloning from `GitRepository(url=GIT_URL, branch=GIT_BRANCH or None)` — a **separate** git fetch from the worker pod's own `git_clone` pull step, and my local shell had no `GIT_BRANCH` set (that's a pod-only `kubectl set env` patch, D37/D39), so it silently fell back to `main`. `entity_follow`'s `force` parameter — added on `feat/control-center`, never merged to main per rule 3 — was invisible to that schema, so the very `ia prefect deploy` meant to fix #4 regressed entity-follow's own deployment, making every `run_deployment(parameters={"force": ...})` call fail validation (`SignatureMismatchError`) even though the actual flow body executed by the worker (sourced correctly via the pod's own `GIT_BRANCH`-aware `git_clone`) has always had `force`. Fixed by re-running with `GIT_BRANCH=feat/control-center` set explicitly. **Any future `ia prefect deploy` run from a local shell (not the pod) needs `GIT_BRANCH=feat/control-center` set first**, or it will quietly break whichever deployment's signature has diverged from `main` — worth a CP 7.1-style fix (read `GIT_BRANCH` from `config.env`/a committed default rather than requiring it in the caller's shell) but not done here, mid-incident.

**Verified end to end, live, no shortcuts:** after all five fixes, a `force_run` command (via the agent's REST API, not the GUI) produced a real `entity-follow` flow run that reached `COMPLETED` in 92.4s — matching historical successful-run durations. ADB held `origin: supervised`, bound `0.0.0.0`, same PID, for the rest of the session (well past the ~30-45s churn window it was breaking at before). Scheduler heartbeat back to `online: true`, sub-2s freshness. All other four flows (`scan`/`scrape`/`classify`/`ingest`) confirmed still gating correctly (`no_work`/`backpressure`) after every restart.

**Shipped, not yet verified over a long unattended window:** the scrcpy pin is a venv hotfix on `wsl-bridge`, not a real release — needs `fix/scrcpy-adb-version-pin` actually merged/released and `wsl-bridge`'s dependency bumped before it survives a `uv sync`. CP 6.2 is now live on the worker for the first time (earlier than rule 3's original plan) — everything downstream of `notify()` (limit-reached messages, unfollow prompts, etc.) is now actually running in production and should be watched.

---

## 2026-08-02 — Phase 6 implementation session (CP 6.3 groundwork, checked before writing any code)

### D54 · Pairing UI lives in a new Settings tab; the notification center is a title-bar bell icon — neither gets a new nav destination

**The gap:** ARCHITECTURE §9's seven nav destinations (Overview · Flows · Live · Services · Library · Insights · Settings) have no slot for either piece PLAN CP 6.3 scopes ("QR screen, paired-device list with last-seen and revoke, notification center with history and per-tag mute"). §9 originally imagined the notification feed living inside Overview, but Overview itself was never built past its CP 0.3 placeholder — no checkpoint in PLAN.md ever scoped it — so building the notification center "inside Overview" would mean building a minimum Overview screen first, unscoped work nothing asked for yet.

**Chosen, asked before any code was written (matching the CP 4.5/CP 5.4 precedent of checking real design forks rather than guessing):**
- **Pairing (QR code, paired-device list, revoke) is a new "Devices" tab in Settings**, alongside the existing Flows/Limits/Queue tabs — no shell changes, fits the established multi-tab pattern for "things backed by machine-local config," which pairing already is (CP 6.1's `pairing.json`).
- **The notification center is a bell icon in the title bar**, opening a dropdown/panel with history, unread state, and per-tag mute — reachable from every screen without requiring Overview to exist, and it's the standard place a user already expects to find this.

**Rejected:** a new top-level nav destination for pairing (grows the rail past ARCHITECTURE's planned seven for a screen that's mostly a one-time setup action), and building notifications inside Overview (blocked on unscoped work).

**Not yet built — this is groundwork only.** CP 6.3 itself starts from this placement decision.

---

## 2026-08-02 — Phase 6 implementation session (CP 6.2, Notifier facade)

### D53 · `notify()`'s Telegram fallback keeps the old search-and-delete dedupe by message text; a live screenshot buffer only reaches Telegram, not the agent; and a real risk was found and flagged, not silently shipped

**`controllers/notify.py`'s `_notify_telegram` reproduces `notify_transient`'s exact old mechanism — search the notify channel for messages with the *same text* as the new one, delete them, then send — rather than inventing a real dedupe-key concept on the Telegram side.** Telegram has no notion of an abstract dedupe key; the two callers that used to route through `notify_transient` (`notify_new_entities_classified`/`_scraped`) always had constant message text, so "same text" and "same dedupe key" were already the same test. Passing `dedupe=` on the limit-reached calls too (whose text embeds a changing count) is safe by construction: the search simply never matches anything, identical to those calls getting no Telegram-side dedupe before this facade existed.

**`notify_profile_unfollow`'s image is a live `ui.profile_header.screenshot()` `BytesIO`, not a file under `IA_DIR` — the one call site that doesn't fit `emit()`'s established IA_DIR-relative-path convention.** The agent's `/api/notify` (CP 6.1) can only cache a path it can read itself; there is no bytes-upload path, and building one for a single call site was out of scope for this checkpoint. `_relative_image()` returns `None` for anything that isn't a `Path`, so the agent-side notification for this one message simply carries no image — Telegram, which receives the original object untouched, still gets the real screenshot regardless of `NOTIFY_POLICY`, since `_notify_telegram` never goes through the relativizing helper.

**Found while wiring this in, not before: `POST /api/notify`'s `delivered` (CP 6.1) counts *any* live WebSocket connection on the shared bus, not a client actually watching notifications — because no such consumer exists in the app yet (CP 6.3 hasn't shipped a notification center).** Under the default `app_first` policy, if the desktop app happens to be open and connected to `/ws` for any reason (Live screen, Flows screen — anything), every `notify()` call across the whole pipeline would read `delivered: true` and skip Telegram, even though nothing currently renders it anywhere. That would be a real, silent loss of every limit-reached/unfollow-prompt/entities-classified message during normal daily use of this very app. **Not fixed here** — the honest fix (per-channel subscription tracking in `events/bus.py`, flagged as future work in its own docstring since CP 4.2) is bigger than this checkpoint, and it doesn't matter operationally yet: this branch (`feat/control-center`) is never deployed to the live pipeline pod until the whole control center is accepted (CLAUDE.md rule 3), and CP 6.3's notification center will exist well before that point. Recorded here so whoever revisits `NOTIFY_POLICY`'s default — or considers merging this branch — checks that CP 6.3 has actually landed first, or narrows `delivered` before then.

**Verified without touching the real Telegram channel or the real running agent.** `Insta-Automate` has no test suite (same precedent as CP 3.1/3.2/4.3) — verification was an import sanity-check across every changed module (`controllers/notify.py`, `tasks/telegram.py`, `tasks/device.py`, `tasks/ia.py`, `flows/entity_scrape.py`, `flows/entity_follow.py`, plus the full `IaFlows` registry and `controllers/cli` to catch indirect breakage) and a throwaway script exercising the facade's actual branching logic (18/18 — `app_first`/`telegram_only`/`both` routing, dedupe search-and-delete, the `Path`-vs-`BytesIO` image split, a missing-file `Path` dropped exactly like the old `img.exists()` guard) against `AgentClient.notify` and `IaTelegram.get_client` monkeypatched to recording fakes, never the real network calls. `AgentClient.notify` itself was already proven end to end against a real agent instance in CP 3.3/CP 6.1; nothing new here re-tests that path. Nothing deployed to the live pod — same standing precedent as every `Insta-Automate` checkpoint since CP 4.3.

---

## 2026-08-02 — Phase 6 implementation session (CP 6.1, Pairing + notification core)

### D52 · Q6/Q7/Q8 answered before writing code — device mirror stays desktop-only, Add Entity posts to Telegram, and every candidate notification category ships

**Q6 — device mirror stays desktop-only, the opt-in phone-glance stream is not built this phase.** CP 4.5 already made this call for the desktop side (D-numbered decision at the time, see PLAN CP 4.5); asked again now that mobile pairing gives a phone a real place to receive a stream, the answer was the same: build the consumer (this phase) before the producer (`device.mirror` broadcast plumbing), not the other way around.

**Q7 — the desktop app's future Add Entity action posts to the Telegram entity channel, not the DB directly.** Zero pipeline changes needed: the existing `NewMessage` handler already fires ingest instantly on a channel post. Matches PLAN's own recommendation. Not implemented this checkpoint (CP 6.1 is pairing/notifications only) — recorded now so whichever checkpoint builds it doesn't re-litigate the choice.

**Q8 — all four candidate notification categories are in scope: limit-reached, new entities classified/scraped, scan-complete/unfollow-prompt, and failures (device disconnected, flow failed, service down).** No category was cut. This doesn't mean every one pushes to a phone unconditionally forever — `NOTIFY_POLICY` and per-tag mute (CP 6.2/6.3) are the actual on/off switches — but the notification *store* built this checkpoint needed to know up front that `tags` is a real, load-bearing field on every entry, not an afterthought, since muting by tag only works if the right tags were being attached from day one.

### D51 · Device tokens are trusted everywhere a desktop token is, except managing pairing itself

**`auth.py`'s bearer check now accepts two token classes with no per-endpoint distinction by default** — the desktop token (file-based, same-machine trust) or any current, non-revoked device token (`PairingStore.authenticate`). Building both into one `is_authorized()` helper, shared by the HTTP middleware and the `/ws` handshake (which `BaseHTTPMiddleware` never wraps — same reason the desktop token needed its own WS-side check from CP 0.2 onward), keeps the two paths from drifting.

**Caught by the pairing test's own first run, not designed in up front: a device token could list and revoke *other* paired phones, and mint new pairing codes.** `/api/pair/start`, `GET /api/pair/devices`, and `DELETE /api/pair/devices/{id}` are desktop-console actions — a phone has no legitimate reason to enumerate or kick off siblings it didn't pair. Fixed with a route-level `_require_desktop()` check in `api/pair.py` that compares the request's credential against the desktop token specifically, layered on top of (not instead of) the outer middleware's already-broader check. `/api/pair/claim` stays reachable with **no** bearer at all — the phone claiming a code has none yet by construction (§7) — everything else a phone will actually need (CP 6.4: config, notifications, live flow view) is left open to both token classes rather than building a scoping system for endpoints that don't exist yet.

### D50 · Notification history is a persisted store, not an in-memory ring like flow events

**`events/store.py`'s `EventStore` is memory-only by design — a flow run's per-item images are worthless the moment the next run starts, so a restart losing them costs nothing.** A notification is the opposite kind of state: "FOLLOW limit reached" sitting unread is exactly what a restart must not silently discard. `notifications.py`'s `NotificationStore` writes its full history to `%LOCALAPPDATA%\ia-agent\notifications.json` on every mutation (add, mark-read), capped at `MAX_HISTORY=1000` so indefinite uptime can't grow the file without bound — same atomic temp-file-then-replace pattern every other `*.json` settings file in this agent already uses (D12's precedent).

**Dedupe replaces a prior notification with the same key only while it's still unread; once read, a repeat is a new occurrence.** This preserves `Insta-Automate`'s existing `tl.bot.notify_transient` search-and-replace semantics (ARCHITECTURE §6) rather than inventing new ones: "SCRAPE limit reached (180/300)" then "(250/300)" is one evolving fact worth collapsing to its latest value, but once you've acknowledged it, a fresh limit-reached notification tomorrow is a distinct event, not an edit.

**`delivered`/`targets` in `POST /api/notify`'s response is the live WS subscriber count at publish time, not per-channel subscription tracking.** `events/bus.py`'s `EventBus` broadcasts every channel to every connected socket today (its own docstring already flags per-client filtering as future work, "once there is more than one channel competing for bandwidth") — so "how many subscribers got this" is honestly answered by "how many sockets are connected," and a `subscriber_count()` method was added to the bus rather than building real per-channel accounting for a distinction that doesn't exist anywhere yet.

**Verified:** new `agent/tests/test_pairing.py` (29/29 — code TTL/single-use, device-token auth working on an ordinary bearer-protected route, the pairing-management scoping fix above, persistence across a fresh `PairingStore`, a real WS connection authenticated with a device token instead of the desktop token) and `agent/tests/test_notifications.py` (30/30 — defaults, image caching reusing CP 4.2's `images.cache` unchanged, dedupe-while-unread, `since=`/`unread_only=` filtering, mark-read/mark-all-read, persistence across a fresh `NotificationStore`, a live `notifications` WS delivery). All eleven prior suites unchanged (71/71, 49/49, 65/65, 36/36, 35/35, 32/32, 26/26, 24/24, 20/20, 16/16, 14/14). Also verified against the real running agent — restarted to pick up the new code (same step every checkpoint since CP 4.4 has needed; all three supervised services confirmed on identical pids across it) — a real pairing round trip (start → claim with no bearer → device token authenticating → revoke) and a real notify round trip (post → list → mark read) against the live `%LOCALAPPDATA%\ia-agent`, leaving one read, tagged `test` notification in the now-real `notifications.json` as the only trace.

---

## 2026-08-01 — Phase 5 implementation session (CP 5.4, Entity view)

### D49 · "Followed" stays a folder-count estimate — no Postgres ledger, deliberately, after weighing where the exact fix belongs

**The gap is real: no per-entity "followed" record exists anywhere.** `entity_follow` sends the request and unlinks the image on every terminal verdict — nothing is ever written to Postgres, so `entity_view.fetch()` can only approximate: `scraped − still in scraped/ − still in follow_queued/`. That's what shipped. Confirmed via your live test as "okay" with the one caveat that it can't be exact, especially for anything followed before this checkpoint existed (unrecoverable — the image is gone, no record was ever kept).

**The exact fix was scoped, not guessed at, before being set aside.** `profile_follow` already emits a `follow.result` event with a real `verdict` for every attempt (`Insta-Automate/tasks/ia.py`), so a real fix is genuinely small: one new SQLModel table, one `session.merge()` alongside the existing `emit()` call sites, no migration system to fight (this repo's schema is a bare `SQLModel.metadata.create_all()`, `controllers/postgres.py` — additive and idempotent). Where to persist it was the real question — weighed against IA_DIR-as-file, agent-local JSON (D12's precedent for machine-local settings), and Postgres — and Postgres won decisively: `entity_follow` already calls `db_backup()` at the end of every run, which `pg_dump`s the whole database to the Telegram backup channel (`db_restore()` to bring it back). Any new table rides that exact mechanism for free — zero new backup infrastructure for you to set up, unlike an agent-local file, which would need one from scratch to survive a laptop reset.

**Set aside anyway, on your call: not worth a cross-repo `Insta-Automate` change for a metric you said you may not use.** This project's own working rules already say not to design for hypothetical requirements — "followed" isn't what the funnel exists to answer (that's scanned → private → female → scraped, "which source entities are worth queueing," per PLAN CP 5.4's own framing), and every cross-repo change carries real weight here (unmerged on `feat/control-center` until the whole control center is accepted, per rule 3). The approximation ships as-is, undocumented as anything other than what it says on the label (`entity_view.py`'s own docstring already spells out exactly what it can't distinguish). If real per-entity follow tracking becomes worth it later, the design above is the one to build: a small Postgres table, written at the same `follow.result` call sites, backed up for free by the flow that already runs.

---

## 2026-08-01 — Phase 5 implementation session (CP 5.3, Library UI)

### D48 · Focus and selection are separate axes, keyboard and mouse both toggle rather than replace, and range-select anchors from whatever was last touched

**Corrected from your live testing, not guessed up front.** The first version required Ctrl+click to add to a selection (plain click replaced it, matching a common "single-select-by-default" file-manager convention) and treated a plain arrow key the same way `selectOnly` treated a plain click — moving focus *and* collapsing the selection to just the new item. Both read as wrong once you tried the actual workflow: "clicking it should toggle the selection... why do I need to press ctrl," and "arrows move the focussed image and space should do the same thing toggle the selection" — arrow-then-space-then-arrow-then-space needs each Space to *add* to the batch, which `selectOnly` made impossible since the very next arrow press had already thrown away the previous pick.

**Fixed by treating focus and selection as genuinely independent state**, not derived from each other: `LibrarySelectionNotifier.moveFocus()` (plain arrow — focus only, selection untouched) is now a distinct operation from `.toggle()` (plain click *or* Space — adds/removes the touched item from whatever's already selected, and becomes the new range anchor). `selectOnly()` is gone entirely; nothing in the UI ever collapses a selection down to one item anymore except `.clear()`. Shift+click/Shift+arrow (`.selectRange()`) were correct from the first version and untouched — they already extended from an anchor rather than replacing it, which is the same "add, don't replace" principle the fix applied everywhere else.

**Ctrl is no longer read from the tile's tap handler at all** (`LibraryTile.onPrimaryTap` dropped its `ctrl` parameter) — a plain click's meaning no longer branches on a modifier, so there was nothing left for it to gate. See [[feedback-multiselect-toggle]] for the durable UX rule this establishes for any future multi-select surface in this app.

**Verified:** `flutter analyze` clean, `flutter test` 32/32 throughout (both before and after the fix — the layout suite checks overflow, not selection semantics, so a dedicated interaction test wasn't warranted for a same-session correction verified live by you). Confirmed working via your own retest ("Thats better") before this checkpoint's docs were written up.

---

## 2026-08-01 — Phase 5 implementation session (CP 5.2, Mutations)

### D47 · Apply/delete mirror the pipeline's own `send2trash`/`shutil.move` split, move targets are a machine-local mapping seeded with the real pipeline shape, and `config.env` writers now share one lock

**`send2trash` for the discarded half, `shutil.move` for the promoted half — matching `insta_automate.utils.move`/`rm_empty_subdirs`, not the mobile app.** Checked the mobile app (`ia_manager`) first, since it already implements this exact review workflow: its `_applyAction` hard-deletes the unselected half via `File.delete()` — no trash, no recovery — while the pipeline's own `utils.py` already uses `send2trash` for every deletion it makes (`move(..., replace=True)`, `rm_empty_subdirs`). PLAN CP 5.2 says "use send2trash so semantics match the Python side," which settles the conflict in the pipeline's favor: `library/ops.py`'s `delete()` and `apply()`'s discarded half both go through `send2trash`; the promoted half uses a plain `shutil.move`, exactly like `utils.move`. A curation mistake from the desktop app is now recoverable from the Recycle Bin — the mobile app's is not.

**Move targets are a new machine-local setting (`library/settings.py`, `%LOCALAPPDATA%\ia-agent\library.json`), not `config.env` — same D12 reasoning as service self-heal/autostart.** The mobile app's `SettingsProvider._folderMappings` is a fully user-configurable per-folder dictionary defaulting to *identity* (apply = "keep selected, delete the rest," no promotion) until the user points a folder somewhere else. This project already knows the real two real human-review promotions ARCHITECTURE §1.1 documents (`gender_valid → scrape_queued`, `scraped → follow_queued`), so `settings._DEFAULT_TARGETS` seeds those directly rather than shipping the mobile app's blank-slate default — a user who never opens a settings screen for this (CP 5.3 hasn't built one yet) still gets the correct behavior on day one. Every other folder defaults to itself, which is a real, useful action on its own: "keep what I selected, discard the rest," with no promotion.

**`apply()` reads the batch fresh from disk rather than trusting the caller's file list.** The caller supplies `selected` (filenames to keep); "the rest" is computed from a real `os.scandir` of that `(folder, entity)` directory at call time, the same authoritative read `GET /api/library/images` would give right now — so a stale client-side selection (a file that arrived or left mid-review, the exact race CP 4.2's image cache exists to dodge elsewhere) can't silently trash or promote something the caller never saw.

**`config.env`'s write lock moved from `api/config.py`'s own `asyncio.Lock()` to a shared `env_file.WRITE_LOCK`.** CP 5.2 is the first time a second router (`api/queue.py`'s new add/remove/reorder) does its own read-modify-write of `config.env` alongside `api/config.py`'s existing `PATCH`. A per-module lock would only serialize writers *within* that module — two concurrent requests, one to `/api/config` and one to `/api/queue/add`, could still race each other's read-modify-write and silently drop one's change. Moved the lock into `config/env_file.py` itself, the one module both routers already import, so every writer serializes against every other one regardless of which endpoint it came in on.

**`POST /api/queue/remove` mirrors `Queue.remove()`'s default `check=True` refusal, not a bare wholesale delete.** The pipeline's own `Queue.remove(entity, check=True)` refuses to drop an entity from `ENTITY_QUEUE` while it still has jpegs waiting in either stage directory, unless the caller explicitly passes `check=False` — removing it from the priority list wouldn't stop the pipeline from working through the backlog, only from doing so *first*, which is a surprising side effect to hide behind an unqualified "remove." The new endpoint takes the same shape: a 409 naming the pending count, with a `force: true` field for a caller (the future UI, with a confirmation dialog) that means it.

**Verified:** `agent/tests/test_library.py` grew from CP 5.1's 32 checks to 65 (settings defaults/persistence/validation, `apply()`/`delete()` unit-level against a scratch tree — identity-mapped cull, real cross-folder promotion preserving `<root>/<name>`, rejecting an absent selection before touching anything, trashing an explicit path list, rejecting paths outside the seven folders — plus the same checks again over the real REST surface). New `agent/tests/test_queue.py` (14/14) covers `GET /api/queue` plus add/remove/reorder end to end, including the `check=True` pending-jpeg refusal, the forced override, a rejected path-shaped name, and confirming `config.env`'s comments/unrelated keys survive every mutation (the same guarantee `env_file.save()` already gave CP 1.1's `PATCH /api/config`). All eight prior suites unchanged (71/71, 32/32, 26/26, 49/49, 24/24, 20/20, 36/36, 35/35, 16/16). Also verified against the real running agent — restarted to pick up the new code (same step every checkpoint since CP 4.4 has needed), all three supervised services confirmed still running with uptime intact across it, `GET /api/library/move-targets` and `GET /api/queue` hit against the real `IA_DIR`/`config.env` (7,007 real `scrape_queued` files across 110 entities, correctly read-only — **no `apply`/`delete`/`add`/`remove` call was made against the real pipeline data in this session**, since those are real, only-partially-reversible actions on the user's actual curation backlog that nothing in this session asked for; the unit + REST test suites' scratch-tree coverage is what stands in for that live check, matching CP 4.2/4.3's own precedent of never mutating the real `IA_DIR`).

---

## 2026-08-01 — Phase 5 implementation session (CP 5.1, Library API)

### D46 · Device control compacted into the header, its model shown instead of the raw serial —
and the scheduler-line border removed for looking inconsistent rather than useful

**Three more small, real corrections from your live testing, landing together as the session's
close-out.** All Live-screen polish, none touching the agent's actual data surfaces (D36–D39) or
the event/counter logic (D40/D41) — those stay as they were.

**Device control moved out of `RunSummary`'s body into a compact `DeviceBar` in the header row**,
sharing the space next to the flow-selector chips rather than a bordered card competing with the log
console for room. Simplified at the same time, per your ask: dropped the status icon, the explanatory
sentence, and the card styling — just a phone icon, a name, and a `Start`/`Stop` button. `RunSummary`
reverts to the single column it had before D45's two-block `Wrap` (that redesign existed specifically
to give Device somewhere to sit beside the details+counters block; once Device left entirely, the
extra structure was no longer doing anything and a plain `Column` is simpler).

**The name shown is now the device model, not the raw 15-digit serial** — "I2201" reads at a glance,
the serial doesn't. New agent-side `_device_model()` (`ia_agent/api/device.py`) reuses the exact
`adbutils` lookup `services/selftest.py`'s own adb functional test already established
(`AdbClient(...).device(serial=...).prop.model`), best-effort — `None` on any failure (adb down,
device not attached), in which case the bar falls back to the serial rather than showing nothing.
**Caught by you, not assumed working:** the first version genuinely worked but the running agent
hadn't been restarted to pick up the new `/api/device` field yet — same "the code changed, the
process didn't" pattern this whole project keeps hitting — confirmed via `curl` against the live
endpoint both before (`model` key entirely absent) and after (`"model":"I2201"`) the restart, with
the three supervised services confirmed still `adopted` with uptime intact across it.

**The left border on scheduler-merged log lines (D30) is gone.** It marked which lines came from the
scheduler pod's own trigger/gate log (merged into the flow's ring) versus the flow's own execution
log — a real distinction, but you read the resulting ragged left edge as inconsistency rather than
signal. Kept one subtler cue instead of dropping the distinction entirely: those lines still render
in a dimmer text color, which doesn't disturb the shared left edge every line now has.

**Verified:** `flutter analyze` clean, `flutter test` 26/26 (25 prior + one new `DeviceBar` case — a
long model name in the header's own, tighter row, since some real phones report far more than
"Pixel 7"). Agent-side `test_device.py` 16/16, `/api/device`'s new field confirmed live against the
real device. Session closes here — Phase 5 is CP 5.1 done, CP 5.2 (mutations) next.

### D45 · Live screen layout, corrected twice more from your own testing: images fixed and tight,
not logs — and the direction was backwards on the first attempt

**Round one (backwards):** first read your "give images breathing room" as "images should grow" —
built D43 with the visualization surface `Expanded` and the log/summary column fixed. **Corrected
immediately** once you clarified: you'd said breathing room was for *logs*, and images — which
already wrap to fill whatever width they get (D44) — don't need to keep growing. Swapped which side
is fixed: log console (in an `Expanded` left column) now gets whatever the window has left; the
visualization surface is the fixed side. Picked the fixed width carefully rather than guessing large:
the app enforces a 1024×700 minimum window (`main.dart`), and an 820px image column (fitting two
D44 cards) would have squeezed the log column to ~204px at that floor — chose 600px instead, leaving
~424px for logs at the true minimum (matching what was already proven safe pre-D43), generous well
beyond that.

**Round two (still not tight enough):** even at 600px, D44's `Wrap` only fit one 380px scrape card
with real slack beside it — visible, still "wasted," per your next screenshot. Tightened to exactly
420px: one `_ScrapeCard` (380) plus the surface's own 16px padding on each side plus a scrollbar
allowance, no rounder number left over. Flagged in code as tuned to scrape specifically (the only
flow tested this session) — follow's own cards are wider (420, D44) and wouldn't fit this tightly;
revisit once that flow gets a real test, per your own stated plan.

**`RunSummary` was also reorganized in this round** (superseded later, same session, by D46 once
Device left `RunSummary` entirely) — worth recording because it's what caught a real bug: capping
the details+counters block to 320px to sit beside a Device block made the "many counters" stress
test overflow a 700px test height by 10px, since the same six chips now wrapped into more rows in
less width than they'd had before. Widened to 380px, confirmed clean — a genuine, would-have-shipped
overflow in an edge case (many counters after a long run id) that only surfaced by rerunning tests
after a width change, not by inspection.

**Verified, each round:** `flutter analyze` clean, `flutter test` 25/25 both times, before D46
superseded the `RunSummary` half of this entry.

### D44 · D43 widened the pane, but the cards inside it didn't use the width — `Wrap` instead of `ListView`

**Found immediately by you testing D43's fix**: the visualization surface really was wider, but
scrape/follow/classify's card lists are all a single-column `ListView` of `Row`-shaped cards (image
left, text right) — each card stretches to the *list's* full width but its own content doesn't, so
the extra room D43 freed just became more empty space to the right of every card, not more visible
information. Every scrape run so far had been tested at the *old*, narrower pane width, so this was
never visible until now.

**Fixed by capping each card's width and `Wrap`ping them, not by redesigning the cards.** A
`SizedBox`-capped `_ScrapeCard`/`_FollowCard`/classify card inside a `Wrap` fills a wide pane with
*more cards side by side* instead of one stretched-and-underfilled card per row — same visual design
each card already had (proven to work at that width by D41/D42's own testing), just packed more
densely. New `_HistoryWrap` in `scrape_surface.dart` (shared between the "all resolved" and the
in-progress branch's history list, both of which needed it); the same pattern inlined directly in
`follow_surface.dart` (420px cards, wider than scrape's 380 — its outcome badge can read
`WANTS_TO_FOLLOW`) and `classify_surface.dart` (320px, since its cards are simpler).

**`ClassifySurface` needed one more change than the other two: it became a `StatefulWidget`.**
`ScrapeSurface`/`FollowSurface` show resolved history that a person browses at their own pace, so a
plain `Wrap` in a `SingleChildScrollView` is enough. Classify streams fast enough to show its own
img/s rate, and the previous `ListView(reverse: true)` got auto-follow-the-newest for free from that
trick alone — a `Wrap` has no equivalent, so it needed the exact `ScrollController` + "did the count
change → animate to `maxScrollExtent`" pattern `scan_surface.dart` already established, applied here
verbatim rather than invented fresh.

**Checked, not applied everywhere:** `ScanSurface`'s own filmstrip is already a horizontally-scrolling
`ListView` of fixed-width items — structurally the same fix already, nothing to change. `IngestSurface`
already uses a `GridView` for the identical reason. Only the three single-column `Row`-card lists had
the gap.

**Verified:** `flutter analyze` clean, `flutter test` 25/25 (existing fixtures, unchanged — `Wrap` is
a standard widget with no custom sizing logic to add new overflow risk, and the existing 700px-wide
overflow tests still validate the worst case, a single card per row). Not yet verified against a live
run / real window at the actual (much wider) production width.

### D43 · Live screen: two columns, not three — summary sizes to content instead of stretching

**The layout itself was the last complaint**, once the data and per-flow visuals were actually
correct: the fixed 320px `RunSummary` column stretched to the window's full height regardless of how
little content it actually had, leaving visible dead space below the device pane, while the
visualization surface — the actual point of this screen, per its own docstring ("the showpiece
screen") — was squeezed into whatever was left between two other panes.

**Chosen: two columns, not three.** Left column (still a fixed 420px) is now a `Column`, not a
`Row` slot: `RunSummary` on top, sized to its own content (a non-flexible `Column` child gets
unbounded main-axis space to size itself — confirmed empirically in the test below, not just assumed
— so it never stretches further than it needs), and `LogConsole` in an `Expanded` below it taking
whatever height that leaves. The right side is now a single `Expanded` visualization surface, which
picks up both the freed 320px and log console's old share of the middle — a real, meaningful width
increase for the panel that actually needed it.

**Summary goes on top, not bottom** — a status glance (phase, today's count, last run, the counters,
device state) reads naturally as "here's where things stand" before "here's the detail log," matching
the same top-to-bottom priority `RunSummary`'s own internal ordering already uses.

**Verified the specific risk this change introduces, not just the width number.** `SingleChildScrollView`
(what `RunSummary` is built on) behaves differently under an unbounded main-axis constraint than
under the fixed `height: 700` every existing test gave it — genuinely worth checking rather than
assuming, since `ListView`/`CustomScrollView` (sliver-based scrollables) throw exactly this shape of
error ("Vertical viewport was given unbounded height") in the same situation. Rewrote both
`RunSummary` tests to reproduce the real constraint shape (`Column(children: [RunSummary(),
Expanded(...)])` inside a bounded outer height, not just `RunSummary()` alone in a fixed box) —
confirmed clean, since `SingleChildScrollView` (unlike its sliver-based cousins) measures its child
directly rather than needing a bounded viewport to lay out lazily. Also widened both `RunSummary`
tests from 320 to 420px to match the column's real new width — 320 was still a technically-valid
(narrower, stricter) case, but no longer representative of what production actually gives it.

**Verified:** `flutter analyze` clean, `flutter test` 25/25 (no new test count — two existing
`RunSummary` cases rewritten to the real constraint shape and width rather than added to). Not yet
verified against a live run / real window.

### D42 · The in-progress scrape card's own image ratio was still wrong, and roots are worth naming

**Found immediately by you testing D41's fix**: the still-in-progress card looked right structurally
(large, correctly scoped) but its image was a tall blank box — because it was still assuming the
scraped composite's portrait shape (`1080/2246`, actually the *entity-page* ratio, not even the
composite's own `1080/2000`) for an image that, while still in progress, is only ever the queued row
crop (`scrape_queued/<root>/<user>.jpg`) — the same wide `1080×198` shape `scanned/`/`gender_valid/`
already are. **Fixed properly this time by rethinking the layout, not just the number:** a wide strip
image doesn't belong squeezed into the portrait Row every resolved card uses, so the in-progress large
card now lays out as a strip on top with the details below, instead of forcing a wide image into a
narrow portrait box. Checked the small/resolved cards too while in there: `scrape.skipped` never gets
a composite either — it was *also* silently assuming the composite ratio for a row-crop image, fixed
to use `1080/198` for skipped specifically (only `scrape.done`, which genuinely has a composite,
keeps `1080/2000`).

**Added "root: <entity>" to both scrape and follow cards** — the source entity a candidate was found
under, i.e. the parent directory in `scrape_queued/<root>/<user>.jpg` / `follow_queued/<root>/<user>.jpg`.
New `rootFromImage()` in `surface_common.dart` (shared, since both flows have the identical
`<root>/<user>.jpg` shape) parses it from whichever event's `image` field is on hand — every event on
a given card carries the same relative path regardless of kind, so which one doesn't matter. Scoped
to scrape/follow only, not scan/classify/ingest — scan's own event already exposes the root directly
as `entity` (it's scanning that root's followers/following, not looking it up from a path), and
classify/ingest's row-crop images don't share this same `<root>/<user>.jpg` two-level structure in a
way that would read the same.

**Verified:** `flutter analyze` clean, `flutter test` 25/25 (no new test count — extended the existing
in-progress-card and follow-verdict fixtures with real `image` paths rather than adding new tests,
since the existing ones were the right places to exercise a long root name for overflow; the shared
`_event()` test helper gained an `image` parameter it didn't have before to make this possible). Not
yet re-verified against a live run.

### D41 · Three Live-screen UX requests, checked per-flow rather than assumed universal

**Your framing mattered here** — all three requests were demonstrated against Scrape (easiest flow
to trigger for testing) but explicitly asked to be applied "wherever relevant," not copy-pasted onto
every surface regardless of fit. Checked each of the other four surfaces before touching anything:

**1. "Large latest card" should track in-progress, not merely most-recent.** Confirmed this pattern
(a big card for the newest item, small history below) only exists in `scrape_surface.dart` and
`scan_surface.dart` — classify/follow/ingest render every item uniformly already, nothing to change
there. `scan_surface.dart` already keys its big banner off `scan.started` specifically (decoupled
from the completed-items filmstrip), so it was already correct. Only `scrape_surface.dart` kept the
latest subject large even after it resolved to `scrape.done`/`scrape.skipped`. Fixed: large is now
conditional on the latest subject still lacking a `done`/`skipped` event; the instant it resolves,
the surface falls back to one uniform small-card list, newest first, no special casing.

**2. Image cropping was two separate bugs, not one.** `AgentImage`'s default `fit: BoxFit.cover`
crops to fill an assumed aspect ratio — fine when the ratio is exact, lossy when it's approximate.
Checked all five real source images (ARCHITECTURE §1.1) against what each surface assumes: `scanned/`
row crops (1080×198 exact) and `entities/<id>.jpg` (1080×2246 exact) match their surfaces exactly —
`scrape_surface.dart`'s `done` card (`1080/2000`) is a *deliberate approximation* of a genuinely
variable height (`profile_scrape` composites a screenshot crop plus a resized avatar, so real height
drifts around ~2000 per profile) — no fixed constant will ever be exact there. `follow_surface.dart`
was outright wrong, not approximate: `1080/2246` (the entity-page ratio) for an image that's actually
`follow_queued/`'s scraped composite (~1080×2000, confirmed by reading `profile_follow`'s own `img`
parameter in `tasks/ia.py`) — a real second bug, not the same one twice. Fixed both: `AgentImage`'s
default is now `BoxFit.contain` (letterboxes instead of cropping — a no-op for the two exact-ratio
surfaces, and correct instead of lossy for the two approximate/wrong ones), and
`follow_surface.dart`'s aspect ratio corrected to `1080/2000` to match scrape's.

**3. Live incremental counters, computed per-flow rather than one generic rule.** The previous design
(D40) read only `flow.completed`'s aggregate, so "Counters this run" stayed empty until the whole run
finished — exactly the "wait for the end" the request was about. There is no single generic
"count something" rule that fits every flow, because each flow's per-item events carry different
shapes: `entity-scan`'s `scan.item` already carries the pipeline's own running `added`/`scanned`
tally per event (just read the latest one, no client-side counting needed); `entity-classify`/
`entity-follow` have no built-in running tally, but their per-item events carry a `verdict`, so a
live count-by-verdict client-side is exactly right (`PRIVATE`/`PUBLIC`, `FEMALE`/`MALE`, or the six
follow verdicts); `entity-scrape` has no `verdict` field, so `processed`/`scraped` are derived by
counting `scrape.done`/`scrape.skipped` occurrences directly; `entity-ingest` similarly counts
`entity.added` occurrences. New `_liveCounters(flow, events)` in `run_summary.dart` dispatches on
`flow` rather than guessing generically, incrementing live as each new per-item event streams in via
WS — no more waiting for `flow.completed` at all for this panel (that event kind is no longer read
here; its counters were always redundant with what client-side tallying now produces sooner).

**Verified:** `flutter analyze` clean, `flutter test` 25/25 (23 prior + 2 new — an in-progress-card
large-layout case for scrape, since the only prior `ScrapeSurface` test's fixture happened to always
resolve its latest subject and so no longer exercised the large-card path at all once this fix
landed; and a follow-verdict-tally case for `RunSummary`, since the prior "many counters" test read
`flow.completed` directly and would have silently tested nothing — an empty "No counters yet." —
under the new per-flow logic. Both gaps were caught by rereading what each test's fixture would
actually now exercise, not just by "tests still pass"). Not yet verified against a live run.

### D40 · Two Live-screen bugs found by real data, once real data finally existed

**Found the moment D39's rebuild made the visualization surface show anything at all** — the Live
screen never had real events to look wrong against until tonight, so these were latent since CP 4.4.

**1. `RunSummary`'s "Counters this run" mixed per-item facts into a run-level summary.** `scrape.done`
carries `counters: {posts, followers, following}` — one profile's own stats, meant for that profile's
card in the visualization surface. `_EventCounters` (`run_summary.dart`) merged *every* event's
`counters` map indiscriminately, last-value-wins per key — so after scraping two different profiles,
the panel showed one of their `posts`/`followers`/`following` (whichever `scrape.done` happened to
land last) labeled as if it were a whole-run fact. Meaningless at the run level either way — summing
follower counts across unrelated profiles isn't meaningful, and neither is showing one profile's
count and implying it represents the run. **Fixed:** only `flow.completed`-kind events (CP 4.3's
"unambiguous whole-run boundary" event, emitted exactly once per run with genuine aggregates like
`processed`/`scraped`) contribute to this panel now. Per-item counters stay exactly where they
already belonged — the per-card display in the visualization surface — and aren't duplicated here.

**2. Stale/orphaned events leaked into every run's display, forever.** `LiveController` scoped events
to the current run with `event.flowRunId == null || event.flowRunId == runId` — a permissive
fallback written back when `flow_run_id` injection didn't exist yet (pre-`f494553`), so *something*
would show up rather than nothing. Now that injection is reliable (confirmed by D39's real event
data), that fallback is pure liability: any event that ever got recorded with a null `flow_run_id` —
this session's own diagnostic probes among them — matches *every* run's filter forever, since `null`
never stops satisfying the OR. Concretely: two ad-hoc diagnostic events posted while chasing D39 sat
in the ring and showed up as phantom "scraping..." cards on the very next real run, alongside the two
genuine ones. **Fixed:** removed the null fallback in both the REST replay (`_fetchEvents`) and the
live WS handler (`_handleWsEvent`) — a `FlowEvent` now only belongs to a run if its `flow_run_id`
actually matches. The in-memory event ring itself was also cleared (an agent restart — it's pure
ephemeral debug/display state, nothing persisted depends on it) to flush the diagnostic events
already sitting in it; real runs going forward stay correctly scoped without needing that.

**Verified:** `flutter analyze` clean, `flutter test` 23/23 (unchanged — no new layout-risk surface,
existing `live_layout_test.dart` coverage still exercises both widgets). Not yet re-verified against
a live run with the fix in place — needs a rebuilt/restarted app and one more real scrape to confirm
the panel now shows only `processed`/`scraped` and the surface shows only the current run's cards.

### D39 · **D36 was incomplete.** Correction: git-based deployment only refreshes the flow's own
top-level file — everything it imports (`tasks/`, `controllers/`, `models/`) stays frozen at
whatever was baked into the worker's Docker image, and needed a real rebuild all along

**Found after D38's fix still didn't produce any per-item events** — `flow.started`/`flow.completed`
fired (proving connectivity, auth, and event storage all worked, per D37/D38), but every per-item
`scrape.started`/`scrape.skipped`/`scrape.done` call inside `profile_scrape` — which CP 4.3 genuinely
added, confirmed present in the pushed source — never arrived. Diagnosed by `kubectl exec`-ing into
the worker pod and directly inspecting what Python actually had loaded:
`inspect.getsource(insta_automate.tasks.ia.profile_scrape)` showed a **version with zero `emit()`
calls at all** — pre-CP-4.3 — and `inspect.getsource(AgentClient.emit)` showed the version *before*
`f494553`'s `flow_run_id` injection. Both came from `/usr/local/lib/python3.12/site-packages/
insta_automate/`, i.e. **whatever was `pip install`ed into the image at build time**, not the branch
the deployment's `git_clone` step pulls.

**The actual mechanism, now understood precisely:** Prefect's `flow.from_source(GitRepository(...))`
does clone the branch fresh on every flow run, and it does load the flow's own entrypoint file
(`entity_scrape.py` etc.) directly from that clone via its file path — so code written *directly in
the flow body* genuinely does refresh with every push (this is why `flow.started`/`flow.completed`,
called inline in the flow body, worked immediately after D36). But that file's own `from
insta_automate.tasks.ia import profile_scrape` and `from insta_automate.controllers.agent import
AgentClient` are ordinary absolute imports, resolved through normal Python import machinery against
whatever's already on `sys.path` — which is the image's site-packages install, since nothing in the
`git_clone` pull step (just a bare clone, no `pip install -e`, no `sys.path` manipulation) makes the
cloned copy of `tasks/`/`controllers/`/`models/` take precedence. **A `git push` alone is therefore
only sufficient for changes made directly in a flow's own top-level file** — everything CP 4.3
actually touches (`tasks/ia.py`, `tasks/ollama.py`, `controllers/agent.py`) needed an image rebuild
all along, which is exactly what D29's original technique already did for CP 3.5 — this session just
hadn't re-learned that lesson before D36.

**Fixed:** `ia build` (from `D:\Coding\Insta-Automate`, on `feat/control-center`, clean tree) — 13s,
`uv pip install git+...@feat/control-center` inside the Dockerfile pins the exact pushed commit
(`f4945537...`, confirmed in the build log) — then `kubectl rollout restart deployment/
insta-automate-worker` (confirmed with you first, given the scope: a real image build + redeploy,
bigger than anything else this session) to pick up the freshly retagged local image
(`imagePullPolicy: IfNotPresent`, same tag `insta-automate:3.6.27-python3.12`, so Rancher Desktop's
shared image store is enough — no registry push needed). D38's `create-work-pool` breakage recurred
on this restart too (expected now — every worker restart does this) and was fixed the same way,
`ia prefect deploy` again. **Verified the fix landed**, not just assumed: `kubectl exec`'d into the
new pod and re-ran the same `inspect.getsource` check — `profile_scrape` now shows 6 `emit()` calls
including `scrape.started`/`scrape.done`, `AgentClient.emit()` now injects `flow_run_id`. Have not
yet re-verified against one more real, device-driven scrape run — that needs you to trigger it.

**How to apply, going forward:** for any future `Insta-Automate` change to land on the live worker,
check *where* the change is. A flow's own top-level file (the `@flow`-decorated function's own body)
refreshes on push alone. Anything it imports from `tasks/`, `controllers/`, or `models/` needs
`ia build` + a worker rollout — always, no exceptions, regardless of how "just a small pipeline
change" it feels like. This also means: don't trust "the deployment's `pull_steps` point at the
right branch" or "the branch is pushed" as proof that live behavior changed — the only real proof is
introspecting what's actually loaded in the running pod (`inspect.getsource`, as done here) or
observing the actual downstream effect (an event landing), the same discipline D36/D37 already
established, just needed one more layer of "don't stop until you've verified the real signal."

### D38 · The worker pod's `create-work-pool` init container is destructive, not idempotent —
restarting the worker pod for any reason orphans every deployment

**Found immediately after D37's fix**, when you Force Ran Scrape again and the worker never picked
it up at all (stuck `SCHEDULED`/`Late` forever, despite the worker showing `ONLINE` and its queue
`READY`). Cause: the worker pod's init container named `create-work-pool` logs, on every pod start,
literally `Deleted work pool 'insta-automate-pool'` followed by `Created work pool
'insta-automate-pool'!` — a **delete-and-recreate**, not a create-if-missing. The restart I did for
D37 (`kubectl set env`, which recreates the pod) triggered this init container, which gave the pool
a brand-new UUID. Every existing deployment (`entity-scrape` etc.) still pointed at the old,
now-deleted pool id, so all six showed `work_pool_name: None` / `status: NOT_READY` — invisible
unless you specifically query a deployment's own record, since the pool itself still shows `READY`
and the worker still registers and polls it fine.

**Fixed:** `ia prefect deploy` (the CLI wraps `IaFlows.deploy_all()` — an existing, dedicated command
for exactly this) run once inside the scheduler pod (confirmed with you first). Re-created/
re-attached all six deployments against the current pool id; all show `READY` again. No pod restart,
no image rebuild. The one flow run that was created while broken (`ruddy-wolf`, `aeb50e85-...`)
stays orphaned permanently — a deployment reassociating later doesn't retroactively fix a run's own
already-stored (now-dangling) queue reference — but that's cosmetic, it just sits as `Late` forever
and nothing depends on it clearing.

**Left open, not fixed:** the `create-work-pool` init container's delete+recreate behavior itself is
unchanged — it lives in the Helmcharts repo's worker pod spec (not audited this session; whoever
touches `Helmcharts/Insta-Automate/templates/worker.yaml` next should look at what actually runs
there and consider making it idempotent, since **any** future worker pod restart — a crash, an OOM,
a routine redeploy, not just a deliberate `kubectl set env` — will silently repeat this exact
breakage until someone notices flow runs aren't being picked up and re-runs `ia prefect deploy` by
hand. Worth an ARCHITECTURE/PLAN note whenever CP 7.1 (ops panel) or a Helmcharts session happens.

**How to apply — chain lesson from D36/D37, continued:** each fix this session revealed the next
problem only once verified end-to-end against real behavior, not just "the config looks right now."
D36 fixed the branch, D37 fixed the missing secret, D38 was caused *by* fixing D37 (restarting a pod
to apply an env var is not a no-op action in this cluster). When debugging a live pipeline gap here,
expect fixing one layer to surface the next, and re-verify with a real trigger after every change
rather than assuming the chain is closed.

### D37 · The worker pod never had `IA_AGENT_TOKEN` — every `emit()` call was 401ing silently

**Found immediately after D36**, when you ran a real Force Run of Scrape after that fix and still
saw nothing: the flow genuinely completed (180/300 scraped, up from 145 — confirmed against
`/api/flow-runs`), but `GET /api/events` on the real agent showed **zero events ever recorded**.
`kubectl exec` into both pods directly (not the deployment spec — the actual running containers)
showed why: the **scheduler** pod has `IA_AGENT_TOKEN` set (matching the real agent's token) and
`GIT_BRANCH=feat/control-center`; the **worker** pod — the one that actually executes `profile_scrape`/
`profile_follow`/`gender_classify` and every `emit()`/`emit_sync()` call CP 4.3 added — had neither.
`IA_AGENT_TOKEN` is deliberately env-only, never `config.env` (D26, since it's a secret), so with it
unset the worker's `vars.IA_AGENT_TOKEN` resolves to `""`, every event POST goes out with an invalid
bearer token, the agent's `BearerAuthMiddleware` 401s it, and `AgentClient`'s entire design (D26) is
to swallow every failure silently so a down agent never disturbs the pipeline — which also means a
*misconfigured* agent connection disturbs nothing either, including never producing an error to
notice. Both env vars were originally set only on the scheduler pod, apparently by hand (neither
appears anywhere in the Helmcharts repo's templates), during some earlier session's live testing —
and the worker never got the same patch.

**Fixed:** `kubectl set env deployment/insta-automate-worker IA_AGENT_TOKEN=<same token>` (confirmed
with you first, since it restarts the worker pod). No image rebuild — same reasoning as D36, it's
just a pod env var. Confirmed the new pod (`...-75fd88d98c-fq2v9`) actually has it post-rollout.
**Not fixed / left open:** this was a manual `kubectl set env` patch, same as the scheduler's own
`IA_AGENT_TOKEN`/`GIT_BRANCH` — neither is in the committed helm chart, so a future `helm upgrade`
without carrying these forward would silently reintroduce this exact bug on the worker (and revert
the scheduler's `GIT_BRANCH` override, which is intentional per D29 — that one's *supposed* to reset
on a real deploy). Phase 7's CP 7.1 (`ops panel`) is where `IA_AGENT_URL`/`IA_AGENT_TOKEN` are
planned to move into helm values properly (ARCHITECTURE, CP 7.1) — until then, if the worker pod
ever gets redeployed for any other reason, this patch needs reapplying.

**How to apply — same lesson as D36, one layer deeper:** "the deployment config points at the right
branch" and "the code that branch clones is current" were both necessary but not sufficient — the
pod actually executing that code also needs the right *runtime* configuration (here, a secret env
var) or its calls fail in a way `AgentClient`'s own swallow-everything design makes structurally
invisible. When a live symptom persists after fixing one plausible cause, don't stop at "that must
have been it" — verify the actual downstream signal (here, `GET /api/events` actually gaining
entries) before declaring it fixed.

### D36 · `feat/control-center` in `Insta-Automate` was never pushed — the Live screen's
visualization surfaces were blank for two sessions because of it, not because of anything missing

**The bug:** you reported the Live screen's middle pane ("visualization surface") reading "No scrape
activity yet for this run" on every real scrape you'd tried since CP 4.4 landed. CLAUDE.md already
predicted this for CP 4.4's own test session ("CP 4.3's `emit()` calls aren't deployed to the live
pod yet"), so the first hypothesis was that nothing had changed. It had — the scheduler pod's
deployments already had `GIT_BRANCH=feat/control-center` set and Prefect's own `git_clone` pull step
confirmed every deployment (`entity-scan`, `entity-classify`, `entity-scrape`, `entity-follow`,
`entity-ingest`) was configured to clone that branch. The actual cause: that pull step clones from
**`https://github.com/SeshuTarapatla/Insta-Automate.git`** (the GitHub remote), not the local
`D:\Coding\Insta-Automate` working copy — and local `feat/control-center` was 3 commits ahead of
`origin/feat/control-center`, including `22a706d` (CP 4.3's own flow-instrumentation commit). So
every real flow run since CP 4.3 was written had been executing whatever code predates it, cloned
fresh from GitHub on each run, with zero `emit()` calls anywhere in it — not a partial rollout, a
complete no-op.

**Fixed:** `git push origin feat/control-center` from `D:\Coding\Insta-Automate` (confirmed with the
user first — still a feature branch, not `main`, consistent with the repo's own "other repos are
feature-branch only, never merged" rule, but pushing to a shared remote is still a step worth a
yes/no). No pod restart or redeploy needed — the worker's `git_clone` step runs fresh on every flow
run, so the very next scrape/scan/classify/follow picks up the real code.

**How to apply — the general lesson:** when a cross-repo checkpoint's own session notes say
"verified via a live round trip against a throwaway agent instance" or "nothing deployed to the live
pod yet," that means exactly what it says — a later session must not assume a prior session's
"looks deployed" (an env var present, a deployment's `pull_steps` pointing the right direction) is
the same as "the code the remote clones is actually current." When something that should be visible
in the live app stays stubbornly blank across multiple real runs, check what the *actual remote git
state* is before re-checking the agent/app code — a local-only commit is invisible to anything that
clones over HTTPS.

### D35 · Recompute-on-touch counts, folder-scoped recursive watching, path-keyed lazy thumbnails

**Cached counts invalidate by recomputing the touched pair, not by tracking deltas.**
`LibraryCounts.touch(folder, root)` always re-`scandir`s the one directory a filesystem change
pointed at and replaces whatever was cached for it, rather than adjusting a running +1/-1 counter.
A watcher batch that coalesces multiple rapid changes into one event, or drops one under load, can
never leave a delta-tracked count permanently wrong — a recompute-on-touch count is only ever as
stale as "since the last touch," and the next touch always corrects it. Cost is a non-issue: even
`scrape_queued`'s busiest real root today is ~136 files, and a full `seed()` across the whole real
`IA_DIR` (433 + 7,042 + 180 files across ~120 directories) measured at **15 ms** in
`check_library.py` — nowhere near where per-touch `scandir` cost would matter. A root's count
recomputing to 0 drops it from the per-entity dict entirely rather than keeping an empty tile —
mirrors the "explain why, don't show something dead" instinct behind D17, just for a count instead
of a terminal pane.

**The watcher passes the seven known stage directories to `watchfiles.awatch()` explicitly, and
watches each recursively** — the opposite of `config/watcher.py`'s deliberately non-recursive
top-level-only watch of `IA_DIR`. That earlier choice was about *dodging* the library folders'
churn; this one exists *because of* it. Passing the seven paths directly rather than watching
`IA_DIR` itself means `.thumbs` (the mobile app's own thumbnail cache) and `.Trash-0` (send2trash's
trash, relevant again from CP 5.2) never wake the watcher, without needing an exclude filter.

**Thumbnails are generated lazily, keyed by path at request time, reusing CP 4.2's
content-addressed `images.cache`/`thumbnail` unchanged** — rather than eagerly hashing every listed
file up front. A virtualized grid (CP 5.3) only ever renders the handful of cells actually on
screen, so hashing and caching bytes for files nobody has scrolled to yet would be pure waste.
Content-addressing already means a file later moved by CP 5.2's `apply`/`delete` mutations doesn't
invalidate an already-cached thumbnail — same bytes, same key, regardless of where the file now
lives (or whether it still exists at all).

**Verified:** `agent/tests/test_library.py` (32/32 — folder taxonomy resolution including
path-traversal rejection, seed/touch counting for both flat and per-root folders, a root dropping
out of `entities()` at zero files, full REST round trip, and a real filesystem write reaching a
`library.changes` WS subscriber) plus new read-only `agent/tests/check_library.py` against the real
`IA_DIR` (seed timing, real entity listing, a real image cached and thumbnailed). All eight prior
suites unchanged (71/71, 32/32, 49/49, 26/26, 20/20, 24/24, 36/36, 35/35, 16/16). Also verified live
against the real running agent: restarted it to pick up the new code (same "the code changed, the
running process didn't" step CP 4.4 needed, D21's launcher brought it back in ~8s), confirmed the
three supervised services stayed `adopted` with uptime intact across that restart, then hit every
new endpoint (`folders`, `entities`, `images` with pagination, `image`, `image/thumb`, the
path-traversal 400) against the real `IA_DIR`'s real 7,655 files and confirmed the WS channel is
live (received real `flows.state` heartbeats over the same socket; no `library.changes` frame
happened to fire in the listening window since nothing was actively scanning/classifying at the
time — already covered end-to-end by the test suite's own real-file-write check).

---

## 2026-08-01 — Phase 4 implementation session (CP 4.5, Device view)

### D34 · Window found by PID, not title; the phone-glance stream deferred until Phase 6 can use it

**Chosen, checked with you before writing any code rather than guessed** (both were real forks, not
implementation details): the plan describes positioning the scrcpy window with `my_modules.win32.
snap_window`, which searches by exact window title — but scrcpy's title varies by phone model, and
both `my_modules` and wsl-bridge are marked "no changes expected" (ARCHITECTURE §8), so normalizing
the title at the source wasn't available. New `ia_agent/window.py` finds the window by **PID**
instead — wsl-bridge's `POST /scrcpy/start` already returns the spawned process's pid, exact, no
cooperation needed from either repo. Uses the same raw `ctypes.windll.user32` approach `snap_window`
already does (no new `pywin32` dependency), just `EnumWindows`+`GetWindowThreadProcessId` to match by
pid rather than `FindWindowW` by title.

**The plan's secondary, opt-in low-fps `device.mirror` stream (so a paired phone can glance at the
mirror) is deferred entirely** — Phase 6 (mobile pairing) doesn't exist yet, so there is no consumer
for that channel today. Building the `adb exec-out screencap` capture loop and broadcast plumbing
now would be untested code with nothing to exercise it until Phase 6 lands; scoped this checkpoint to
the primary desktop path only.

**`POST /api/device/scrcpy/start` refuses to cycle an already-running mirror** — same "don't be rude"
reasoning `test_wsl_bridge()`'s existing selftest already established (D-less precedent, just
followed here): `wsl-bridge`'s own `start()` calls `stop()` on the way in, so restarting an active
mirror would throw a new window on screen and interrupt whatever the mirror was being used for. The
snap is retried for up to 5s after a successful start, since the window doesn't exist the instant the
process does — and a snap that never lands still reports the start itself as successful, since the
mirror came up fine regardless of whether the agent could reposition it. `snap_to_known_position`
only re-asserts the exact position `my_modules.scrcpy.Scrcpy.start()` already requests at launch
(`--window-x=1 --window-y=45`) and reads the window's current size first, so it is purely defensive
(a compositor/DPI quirk ignoring the launch hint) and can never resize or distort the video.

**Found while verifying the window-finding mechanism against a real process, not a mock:** the first
attempt spawned a throwaway Notepad and called `find_window_by_pid` on its launched pid — found
nothing. Windows 11's own Notepad turned out to be a packaged app where the pid `subprocess.Popen`
returns is not the pid that owns the window (confirmed via `EnumWindows` dumping every visible
window's owning pid — a different, unrelated pid owned "Untitled - Notepad"). This is exactly D11's
"the pid that binds a port/owns a window is rarely the pid you launched" pattern, just a target this
project hadn't characterized yet — Notepad, not anything this project spawns. Switched to the
machine's actual already-running `scrcpy.exe` (found via `psutil` by name, read-only — nothing
started, stopped, or moved) and confirmed: `where scrcpy` resolves to the exact same path as the
running process's `.Path`, i.e. a real winget-installed native exe with no shim/trampoline in the
chain, and `find_window_by_pid` correctly locates its window. The mechanism is verified correct for
its real target; Notepad was simply the wrong thing to test it against.

**Verified:** `agent/tests/test_device.py` (16/16 — every REST branch: already-mirroring skip, the
snap retry loop succeeding after several tries, a snap that never succeeds not failing the start,
both wsl-bridge failure paths as 502s — against a monkeypatched `wsl_bridge`/`window`, never the real
bridge or a real window). `agent/tests/check_device.py` (new, read-only) then confirmed the real
mechanism against the machine's actual scrcpy process, as described above. `flutter analyze` clean,
`flutter test` 23/23 unchanged (no new layout risk beyond what `RunSummary`'s existing test coverage
already exercises).

---

## 2026-08-01 — Phase 4 implementation session (CP 4.4, Live screen)

### D33 · The Live screen resets on a new run id, not on every heartbeat tick; a shared flow-name lookup instead of a duplicate one

**Chosen:** `LiveController` watches `selectedFlowProvider` (rebuilds `build()` on a flow switch)
but only `ref.listen`s `flowsControllerProvider` — a heartbeat arrives roughly every 2s and would
otherwise force a full `logs`/`events` refetch on nearly every tick for no reason, since almost none
of those change anything relevant. The listener compares `flows[currentFlow]?.lastRun?.id` against
what was last seen and only re-fetches when that id actually changes (a new run started), mirroring
`FlowsController`'s existing "listen for the interesting change, don't rebuild on every emission"
shape rather than inventing a new one.

**`flowTitle`/`phaseLabel` moved from `flow_card.dart` (private) into `scheduler_models.dart`
(shared)** rather than copied — the Live screen's `RunSummary` needs the exact same flow-name and
phase display strings `FlowCard` already has, and a second copy would drift the moment either one's
labels changed. `flow_card.dart` updated to use the shared versions; `flutter test` (23/23,
including the pre-existing `flows_layout_test.dart`) confirms the refactor didn't change `FlowCard`'s
behavior.

**`AgentImage` fetches through `dio`, not `Image.network`** — the images endpoint is bearer-token
gated (same auth as every other agent call), and `Image.network` has no way to attach one. A
`FutureProvider.family<Uint8List, (String key, int? width)>` does the fetch and lets Riverpod's own
caching avoid re-requesting a key already seen at a given width, rather than building a bespoke
image cache.

**Found only by the new `live_layout_test.dart`, not `flutter analyze`** (D19's overflow-is-
paint-time lesson, again): `AgentImage`'s "image unavailable" placeholder (icon + label) overflowed
when shown at the classify surface's 1080:198 row-crop aspect ratio sized to a card thumbnail —
~18px tall, nowhere near enough for icon + spacing + text at their natural size. Every other surface
happened to use taller aspect ratios and never triggered it, which is exactly why a real widget test
matters here rather than eyeballing one or two surfaces. Fixed with `FittedBox(fit:
BoxFit.scaleDown)` around the placeholder's `Column`. Seven new test cases target the same
"unbounded-length real string in a fixed-width pane" shape `flows_layout_test.dart` established: a
60-character username, a 40-character no-space digit run standing in for a pathological detail
string, and six counters shown at once.

**Verified:** `flutter analyze` clean, `flutter test` 23/23 (16 prior unchanged + 7 new). No flow
ran live during this session, so the log console (works today — CP 4.1's tailer reads Prefect's own
execution log, no pipeline-side dependency) and the visualization surfaces (need CP 4.3's `emit()`
calls actually deployed to the live pod, which hasn't happened) are both left for a real end-to-end
check once something runs.

**Corrected after your live test, same session: `_LogLine`'s original rendering was hard to read.**
The first version packed level + message into one `RichText` span with 1px of vertical padding
between lines, everything in monospace, the level shown as inline colored text rather than a
badge — dense in a way that read fine to me reviewing the code but not in the running app with a
real 62-line scrape log. You compared it against Prefect's own log view as the "too far the other
way" reference point — not asking for that level of chrome (no task-run sidebar links), just real
readability. Rebuilt as a row: a fixed-width timestamp, a colored level *pill* (background tint +
bold text, not inline color), and the message in the theme's normal body font at 1.4 line height —
monospace dropped entirely, since these are prose log lines, not aligned tabular data. Scheduler-
sourced lines (D30) keep a visual distinction but as a muted left border accent instead of italics,
which was adding strain rather than clarity. Also surfaced during this same live test: the
scheduler pod's `IA_AGENT_URL not found in config.env` warning, visible for the first time only
because D30's merge exists now — not a new occurrence (it's fired on every heartbeat since CP 3.4/
D28), just newly observable. Fixed at the source by writing the coded default
(`http://172.19.16.1:8787`) into the real `config.env` directly, since `IA_AGENT_URL` is
deliberately excluded from the app's config schema (D26) and has no UI path to set it.

---

## 2026-08-01 — Phase 4 implementation session (CP 4.1, log aggregation)

### D30 · Flow-run log tailing: heartbeat-first discovery, per-run rings, scheduler-pod lines merged by append order

**Chosen:** `ia_agent/flowruns.py`'s `FlowRunTailer` ticks every `TICK = 1.0`s. Active-run
discovery (ARCHITECTURE §5.2) checks the scheduler mirror first — any flow whose heartbeat reads
`phase == "running"` hands over `last_run.id` directly, since `Deployment._last_run` (pipeline
side, CP 3.2) already carries the in-progress run's real id regardless of state, no pipeline change
needed. Falling back to Prefect's own `flow_runs/filter` (state type `RUNNING`, filtered to the five
deployment ids resolved once and cached) only fires when the mirror is offline or reports nothing
running — the gap right after an agent restart, before any heartbeat has landed.

Each tracked run gets its own `Ring` (structured entries: `seq`, `ts`, `source`, `level`, `task`,
`message`), polled via `POST /logs/filter` with `timestamp.after_=<cursor>` — exclusive, so the
same-timestamp boundary is deduped by log `id`, not by timestamp, since two rows in one tick
legitimately share a timestamp. `task_run_id` → task name is resolved once per id and cached
process-wide (`GET /task_runs/{id}`), not per row.

**The scheduler pod's container log (where trigger/gate decisions print, not inside any flow run)
is merged by writing its lines directly into every currently-active run's ring**, in the order
observed — not by a timestamp-sorted interleave with a separate seq space. This reuses D18's
already-accepted precedent exactly: a ring's `seq` means "the order this was appended," and replay
correctness follows from that, not from wall-clock ordering. The alternative (merge-at-read-time by
sorting two independently-seq'd streams by `ts`) would need seq to be reassigned per request, which
breaks the "since= means resume, never re-see, never gap" contract every other channel in this repo
holds. A concurrent-flows edge case exists (two flows "running" at once both get every scheduler
line) — accepted as harmless duplication rather than engineered around, since it is rare.

A run that leaves the active set is still polled for `FINISHED_GRACE = 5.0`s to catch trailing log
lines (Prefect's own log-write lag is a few hundred ms, not zero), then frozen — replayable via
`?since=` forever after, but no longer costing an API call every tick. `RETENTION_RUNS = 20`: oldest
*inactive* ring is evicted once exceeded; an active run is never evicted regardless of count.

**REST** (`api/flowruns.py`): `GET /api/flow-runs?limit=` always asks Prefect directly (cheap, one
POST, always authoritative) rather than only listing what this agent happened to tail, annotating
each row with `active` from the local tailer. `GET /api/flow-runs/{id}/logs?since=` replays the
local ring (`live: true`) when one exists; a run this agent never tailed — from before this agent
started, or one that finished without ever being "active" while it was up — gets a one-shot fetch
straight from Prefect instead (`live: false`, real content, no further updates). **WS**:
`flowrun.logs`, one channel, every new entry tagged with its `flow_run_id`/`flow` — matches D6's
existing "the app filters by channel and payload, not per-run subscriptions" shape.

**Measured, not reasoned — the installed `kubernetes` client's `read_namespaced_pod_log` silently
drops `since_time`.** ARCHITECTURE §5.2 assumed an absolute cursor; live against the real cluster,
passing `since_time` raised `ApiTypeError: unexpected keyword argument` — the generated Python
bindings for this endpoint never wired that parameter up at all (a known gap in the client, not a
server limitation: the k8s API itself accepts it fine). Switched to `since_seconds` (relative),
computed each poll from `time.time() - cursor`, with the caller re-filtering the returned window
against the exact parsed timestamp — the same "trust nothing about the boundary, dedupe yourself"
shape `run_logs` already needed for its own `after_` cursor.

**Also measured: this client version hands back `str(bytes)` for this one endpoint** — the literal
characters `b'2026-08-01T...'`, not real bytes and not decoded text — rather than the plain string
every other call in `integrations/kube.py` gets. `_decode_pod_log` detects the `b'`/`b"` prefix and
`ast.literal_eval`s it back before decoding UTF-8; every other kube.py function was unaffected and
left alone.

**Verified:** `agent/tests/test_flowruns.py` (36/36) — `Ring` seq/replay, both discovery paths,
per-run polling (boundary dedup, task-name caching, level mapping), scheduler-pod merge scoped to
active runs only, eviction protecting active runs, and a live app exercising every REST endpoint
plus a real `flowrun.logs` WS delivery — all with `prefect`/`kube` module functions monkeypatched,
same convention as `test_scheduler.py`'s `build_specs` swap. `agent/tests/check_flowruns.py` (new,
read-only) then ran the *real* functions against the live Prefect server and k3s cluster — resolved
all five deployment ids, listed real recent flow runs, fetched real logs for one and resolved a real
task name, and tailed the real scheduler pod's container log end to end, which is what caught both
`since_time` and the bytes-repr quirk above; nothing it touches is capable of starting, stopping, or
otherwise mutating a flow run, pod, or service. All five prior suites unchanged: 71/71, 32/32,
26/26, 24/24, 20/20. `test_ui_contract.py`'s `terminal_available` `KeyError` reproduces identically
on a clean `main` with none of this session's changes applied (confirmed via `git stash`) — a
pre-existing issue, not a regression from this work, and out of scope for this checkpoint.

### D31 · Flow-event images are cached by content hash, not by source path; events are a loose dict like the heartbeat

**Chosen:** `ia_agent/images.py`'s `cache(rel_path)` keys the cached bytes by `sha256(data)`, not by
`rel_path` — two events pointing at byte-identical files (a duplicate scan hit is the obvious case)
share one cache entry instead of two, and the key stays meaningful forever even though the source
path is usually gone within moments (`entity_classify` unlinks public profiles, `entity_follow`
unlinks right after acting — ARCHITECTURE §5). A missing source file is not an error: `cache()`
returns `None` and `EventStore.record()` still records the event with `image_key: null`, because
the event itself (a verdict, a counter, a reason string) is worth keeping even when the image race
was lost — losing the picture should never mean losing the fact.

**`POST /api/events` accepts a loose dict, not a validated `FlowEvent` pydantic model** — the same
choice `SchedulerMirror.heartbeat` made (D26/D27's precedent). `emit()` (CP 4.3, not yet built) is
fire-and-forget with a 1s timeout and doesn't read the response; a 422 from strict validation would
be a silently dropped event with nobody positioned to notice, so the agent takes whatever shape it's
given and fills in `seq`/`id`/`ts` only when the caller left them out.

**Thumbnails are generated lazily per requested width and cached alongside the original**, not
pre-rendered at a fixed set of sizes on ingest — most cached images are never viewed at every width
the UI might eventually ask for, and ingest-time is exactly when the agent is racing a flow's
`unlink()` call, so doing only the minimum (copy the bytes) there and deferring resize work to first
view keeps that race as short as possible.

**Verified:** `agent/tests/test_events.py`, 35/35 (identical content → identical key, different
content → different key, the missing-file race, thumbnail proportions and width clamping, replay,
and a live app round-trip including a real WS delivery) — see PLAN.md CP 4.2 for the full count.

---

## 2026-08-01 — Phase 4 implementation session (CP 4.3, flow instrumentation, `Insta-Automate`)

### D32 · `emit_sync` blocks for real; a fire-and-forget `create_task` would have lost the image race it exists to win

**Chosen:** `tasks/ollama.py`'s `remove_public`/`gender_classify` are the only two ARCHITECTURE §5.1
call sites that are plain sync functions rather than `async def` — every other instrumented site
(`tasks/ia.py`, all five flow bodies) can just `await AgentClient().emit(...)` inline. The first
version of `controllers.agent.emit_sync` used `asyncio.get_running_loop().create_task(...)` to
fire-and-forget from sync code without blocking it, on the reasoning that both functions are always
called from inside an already-async flow body, so a running loop always exists to schedule onto.
**That reasoning was correct and the design was still wrong**: `remove_public` calls
`entity.unlink()` and `gender_classify` calls `move(entity, ...)` on the *very next line* after the
classification, inside a `for` loop that never once yields back to the event loop until the whole
function returns. A task scheduled with `create_task` doesn't get a turn to run until then either —
so by the time any of those scheduled event-emission coroutines actually executed, every public
profile in the batch had already been unlinked and every classified image already moved. This is
exactly the race `images.cache()` (D31) exists to win, defeated by the very code meant to feed it.

**Fixed: `emit_sync` makes a real, blocking `httpx.post(...)` call**, synchronously, before returning
control to the caller — a module-level function, not an `AgentClient` method, since it needs no
persistent connection (one request per call, immediately). This guarantees the agent has read the
image bytes before `unlink()`/`move()` runs on the next line, at the cost of one blocking HTTP
round-trip per classified image — negligible next to the AI inference call the same loop iteration
already makes. Same failure-swallowing contract as `AgentClient.emit`: any exception (agent
down, endpoint doesn't exist, network blip) is caught and discarded, never allowed to break a
classify run.

**Also found and fixed while verifying this against a real Prefect server**: CP 4.1's
`ia_agent/integrations/prefect.py` `run_logs()` defaulted to `limit=500`, and `flow_runs_filter()`
would silently accept any caller-supplied `limit` too — but Prefect's `/logs/filter` and
`/flow_runs/filter` both 422 above `limit=200` (`"Invalid limit: must be less than or equal to
200."`). CP 4.1's own test suite never caught this because its Prefect calls are monkeypatched
fakes with no such constraint, and the live `check_flowruns.py` run at the time happened to pass an
explicit small `limit=`. The failure mode was silent in production too: `FlowRunTailer._tick()`
catches every exception per-tick and logs it, so a real active run's logs would simply never tail —
no crash, no visible symptom beyond an empty log console. Fixed with a shared
`MAX_FILTER_LIMIT = 200` clamped inside both functions, so every caller (present or future) is
protected regardless of what limit it asks for.

**Verified:** import sanity-check on every changed `Insta-Automate` module (no test suite exists in
that repo — same precedent as CP 3.1/3.2, verified by direct call instead). A live round trip against
a throwaway `ia-agent` instance: `AgentClient.emit` (async) and `emit_sync` (blocking) both pointed
at it via monkeypatched `Config.get`/`controllers.agent.IA_AGENT_TOKEN` (the latter had to be patched
on the *importing* module, not `insta_automate.vars` — a from-import binds its own copy of the name,
the same reason `ia_agent/images.py`'s test monkeypatches its own module's `IA_DIR`, not
`ia_agent.vars.IA_DIR`), both confirmed to land on `POST /api/events` and read back correctly from
`GET /api/events`. The limit-clamp fix was verified directly against the real Prefect server at its
old failing size, then passing; `agent/tests/test_flowruns.py` (36/36) unaffected.

**Corrected same session, before any UI consumed it:** every `emit()` call's `flow` field used
`entity_scan`-style underscores at first, matching ARCHITECTURE §5's literal comment
(`flow: str  # entity_scan | entity_classify | …`). But the scheduler heartbeat and flow-runs API —
both already shipped and already read by the Flutter app (`flowOrder` in `scheduler_models.dart`) —
use hyphenated names (`entity-scan`), an arbitrary string chosen in `Deployment("entity-scan")`
independent of Prefect's own (underscored) flow-function name. Building the Live screen means
joining `flow.events` against `flows.state`/`flow-runs` data by flow name, so two conventions for
the same identifier would force string-translation at every join for no benefit. Re-hyphenated every
`emit()` call (`tasks/ia.py`, `tasks/ollama.py`, all five flow bodies) to match the already-embedded
convention instead — cheaper to fix now, before any downstream code depends on the wrong one, than
to discover it while building CP 4.4.

---

## 2026-07-31 — Phase 3 implementation session (CP 3.5, Flows UI)

### D29 · `force_run` bypasses the rate gate and the switch, never the no-work gate; `pause`/`resume`/`reload_config` stay unwired

**Chosen:** `Prefect` gained `self._commands: dict[str, list[str]]`, `_consume`/`_pending`
(pop-once vs. peek), and `_trigger_gate(force)` (`controllers/prefect.py`). `heartbeat_loop`
(D28) now actually queues the commands it receives instead of just logging them. `wait_until`
(D25) treats `skip_wait`/`run_now`/`reload_config` identically — all three just mean "wake this
wait now instead of at the deadline" — consuming whichever arrives and returning its name instead
of `"elapsed"`. `force_run` is handled per gate site instead: one `force =
self._consume(flow, "force_run")` per loop iteration, reused everywhere that iteration's gate is
checked (`and not force` on a day-limit check, `or force` on a no-work/backpressure check).
`wait_day_change` gained a **peek** (`_pending`, not `_consume`) so a `force_run` arriving while
already inside a day-pause unsticks it without the command being silently consumed before the
outer loop's trigger branch ever sees it.

**The bypass rule: force skips *rate* gates and the switch, never a *no-work* gate.** A day-limit or
backpressure gate is pure rate-limiting — bypassing it is exactly what "force" should mean. A
no-work gate (nothing queued) is a hard constraint — `entity-scan` needs a real queued `Entity` to
supply the `url` parameter, `entity-follow` needs real files in `follow_queued/`, so force can't
manufacture either and those checks are untouched. `entity-ingest`/`entity-classify` have no such
parameter requirement (they just re-check their own directory/Telegram state at run time), so their
no-work gates *are* force-bypassable — a forced trigger with nothing new just completes
immediately, which is harmless.

**Corrected after your first live test: force also bypasses the switch.** The original version of
this decision left the `ENTITY_*` switch untouched by any command, reasoning that force overrides a
rate limit, not an explicit "don't run this." You tested it and disagreed — "the toggles are only
for auto runs, force run should always run irrespective of toggle" — so `Deployment.trigger()` gained
a `force: bool = False` parameter; `if not self.switch() and not force: return` replaces the old
unconditional switch check, and every trigger-loop call site now passes its own `force` through
(`entity_ingest_trigger` needed a `force` parameter threaded in too, since it's called from both the
timer loop and the live Telegram handler — only the timer loop's forced calls pass `True`). A
switched-off flow now really does run when forced, logging that it's doing so.

**`pause`/`resume`/`reload_config` are validated at the agent's REST layer (`KNOWN_COMMANDS`, CP
3.4) but deliberately not wired into the pipeline.** Nothing in the Flows UI has a button for them —
the CP 3.5 plan text and manual test only call for Run now / Force run / Skip wait — so wiring
pause/resume handling now would be dead code with no caller. Whoever adds a Pause button later
wires it the same way `force_run` is wired here: peek/consume against `self._commands`.

**"Run now" and "Skip wait" are one interrupt, not two buttons.** The plan bullets say "Run now"
and "Force run"; the manual test says "press Skip wait." Reconciled by making the Flows card's
first button send `skip_wait` and relabel itself — "Run now" when idle, "Skip wait" when
`phase == "waiting"` — since `wait_until` treats both commands identically anyway.

**Verified without any live Telegram/DB/device/Instagram call** (flow switches are live —
firing a real flow during a test was not acceptable): `Prefect.__new__(Prefect)` skips `__init__`
entirely (no `IaTelegram`/`IaSession`/`AgentClient` construction), then `_consume`/`_pending`/
`_trigger_gate`/`wait_until`/`wait_day_change` are exercised directly with short-circuited `Config`
overrides — mirrors CP 3.2's own verification technique for `wait_until`. All pass: normal elapse is
unchanged when no command is queued, `skip_wait`/`run_now`/`reload_config` each wake `wait_until`
early and are consumed exactly once, `wait_day_change` returns on a pending `force_run` without
consuming it, and the per-flow force-bypass boolean conditions match the table above.

**Flutter side** (`app/lib/features/flows/`, `core/scheduler_models.dart`): `FlowsController`
mirrors `ServicesController`'s shape but replaces the whole snapshot on every `flows.state` event
rather than patching by name, since the channel already publishes the full picture (D27). The
countdown ring's proportional fill needs a "started at" the state block doesn't carry (only the
deadline) — tracked client-side, reset whenever `next_trigger_at` changes, which is what makes a
mid-wait `FOLLOW_WAIT` edit or a `skip_wait` re-target the ring immediately rather than jumping.
"Jump to its logs" opens `http://localhost:4200/flow-runs/flow-run/<id>` in the browser via a new
`FileOpener.openUrl` (same `ShellExecute` call already used for files) — CP 4.1's in-app log viewer
doesn't exist yet, and Prefect's own UI already has the real logs for that run. The switch-disable
confirmation dialog (`_disableConsequence` + the dialog itself) moved out of `switches_tab.dart`
into `core/flow_switch_confirm.dart` so the Settings tab and the Flows card share one copy instead
of forking the consequence text.

**Found by `flutter test`, not `flutter analyze`** (same class of bug as D19/CP 2.4 — overflow is
paint-time): `FlowCard`'s `Card` needed `margin: EdgeInsets.zero` (Material's default 4 px margin
was invisible in the mental model of the card's fixed 360 px width) and the Run now/Force run
button pair needed to become a `Wrap` instead of a bare `Row` — two `OutlinedButton`s at their
natural width came within a couple of pixels of the card's content width, which is exactly the kind
of thing a fixed-width card doesn't get a second chance to reflow out of. `test/flows_layout_test.dart`
(4 cases, one fixed viewport since — unlike the Services detail pane — this card's width doesn't
depend on window size at all) pins both fixes.

**Also found in your first live test: Force Run fired the deployment, but `entity-follow` itself
still refused to follow anyone and sent its own "limit reached" notification.** `force_run`
(this decision, above) only ever bypassed the *trigger loop's* gate — the flow body it triggers,
`flows/entity_follow.py`, independently re-checks `Follow.fetch(session).limit_reached` and breaks
its own loop immediately if the cap is already hit, which it still was (force doesn't touch the DB
counts, only whether the trigger loop calls `run_deployment` at all). Same shape in
`flows/entity_scrape.py`. Both flows gained a `force: bool = False` parameter; the loop conditions
became `(limit_reached and not force)` / `(force or not limit_reached)`, and the day-cap Telegram
notification is now skipped (logged instead) when `force` is set — the whole point of forcing was to
override that constraint, so re-notifying about it is noise, not signal. `entity-scan` needed no
equivalent fix — it only checks `limit_reached` *after* processing its one entity, purely to decide
whether to notify, so it was never gated by the flow body at all. `entity-ingest`/`entity-classify`
have no daily cap. `controllers/prefect.py`'s `entity_scrape_trigger`/`entity_follow_trigger` now
pass `parameters={"force": force}` alongside the existing `force=force` (switch bypass) — two
different mechanisms at two different layers (control-plane trigger vs. flow-body execution), both
needed.

**Discovered while fixing that: flow *bodies* deploy from the git remote's default branch, not
whatever's baked into the image.** `IaFlows.deploy_all()` uses Prefect's `GitRepository(url=GIT_URL)`
storage — the worker clones flow source fresh from git **at run time**, on every flow run, entirely
independent of what `ia build` baked into the image from the checked-out branch. `controllers/
prefect.py` (the trigger loop) is part of the *installed package*, so it picked up `feat/
control-center` correctly when the image was rebuilt from that checkout — but `flows/entity_follow.py`
never would have, no matter how many times the image was rebuilt, because `GitRepository` with no
`branch` clones the remote's default branch (`main`). This had never come up before this session
because no earlier CP touched a `flows/*.py` file. Fixed with a new `GIT_BRANCH` env var
(`vars.py`, empty by default = today's behavior unchanged) threaded into
`GitRepository(url=GIT_URL, branch=GIT_BRANCH or None)` — set via `kubectl set env` on the live
`insta-automate` deployment only for this testing session (same imperative, easily-reverted pattern
as `IA_AGENT_TOKEN`), never baked into the image or committed as a standing override. Once the
control center is accepted and `feat/control-center` merges to `main`, this stops mattering — the
default branch *is* the deployed one again.

**Also found in your first live test: nothing edits `FOLLOW_WAIT` (or any of the other ten trigger
timings) anywhere in the app.** CP 3.1 added them all to `Config._DEFAULTS` on the pipeline side, but
the agent's `config/schema.py` — the only thing `GET/PATCH /api/config` and the Settings > Limits tab
actually know about — never got them, so they were readable only by hand-editing `config.env`. Fixed
by adding a `ConfigGroup.TIMING` and all eleven timing keys plus `SCRAPE_RESERVE_FACTOR` to
`SCHEMA`, and adding `'timing'` to `limits_tab.dart`'s `_groupOrder`. Nothing else needed to change —
`PATCH /api/config`'s limits handling was already generic over any `ConfigType.INT` schema key (the
four cross-checks reference specific keys by name and don't iterate the rest), and `LimitCard` is
already generic over any `ConfigKeySchema`. The whole fix was two data additions, no new plumbing.

**Second round of live-test feedback, same session:**

- **`SCRAPE_BACKPRESSURE_FACTOR` renamed to `SCRAPE_RESERVE_FACTOR`.** Your framing — "if follow is
  60/day, reserve is 180 (60×3); if scraped+follow_queued matches that we're good" — is a clearer
  read of what the number means than "backpressure," so the config key, its `SCHEMA` help text, and
  ARCHITECTURE §4.1 all changed. Nothing had persisted the old name to any live `config.env` yet
  (still resolving to the coded default), so this was a pure rename, no migration.
- **`LimitCard`'s header row could overflow** — exactly this key, whose new name is still 21
  characters. The name `Text` had no width constraint before the fixed-width value field, so a long
  enough key pushed the field outside the card (visible in your screenshot: the number box sitting
  outside the card border). Now wrapped in `Expanded` + `Tooltip` + ellipsis, the same shape of fix
  as the gate-detail text elsewhere — a card of fixed width can't get a second chance to reflow out
  of an overflow, so anything of unbounded length inside one needs this treatment on sight, not just
  where it's already been caught once.
- **The "Triggering" phase label was live for the entire run, not just the moment of triggering.**
  `Deployment.trigger()` calls `await self.log_status()` by default (`wait=True`), which blocks until
  the flow run reaches a terminal state — so `_set_state(flow, phase="triggering", ...)`, set once
  right before that call, was the only phase update for the run's *entire* duration (your Follow
  example ran 116s). Renamed the phase value itself to `"running"` everywhere it's set — accurate for
  what it actually describes for that whole span, not a relabel of a genuinely momentary state.
- **Maximized-mode title bar showed doubled/ghosted window buttons.** Root cause: Windows redraws its
  own caption chrome under/over this app's custom-drawn minimize/maximize/close icons only when the
  window is in true OS-maximized state (a known interaction between `window_manager`'s hidden title
  bar and Windows 11's non-client rendering — restored mode is unaffected, matching what you saw).
  Fixed at the app level rather than patching the plugin: `_WindowButtons` (`shell/title_bar.dart`)
  no longer calls `windowManager.maximize()`. It fakes it via `setBounds` to the monitor's real work
  area, read directly from Win32 (`core/window_work_area.dart` — `GetMonitorInfo`'s `rcWork`, the same
  "reach into Win32 when the Dart wrapper falls short" reasoning as `FileOpener`'s `ShellExecute`
  calls, D5) so the window never actually enters the state that glitches. Tracks `_maximized` locally
  and the restored bounds to reverse it; a `WindowListener` keeps that flag in sync if something
  external changes the real maximize state. **Known gap:** OS-level maximize gestures that don't go
  through this button — Win+Up, dragging to the screen's top edge, the taskbar's own right-click menu
  — still invoke genuine Win32 maximize and can still glitch; intercepting those would need native
  platform-channel work, out of scope here. Unverified by me — I can't hover/click the app myself
  (rule 5) — this is reasoned from the screenshot and the "restored is clean, maximized isn't" split
  you described, not confirmed against a running window.

**Third round: Force Run's disabled state contradicted your actual mental model of it.** It was
built disabled whenever `gate.ok == true`, on the reasoning that Skip Wait already covers "nothing's
blocked, just wake the timer." Your framing corrected that: there are only two kinds of trigger —
*scheduled*, which always respects every condition, and *manual*, which should run and complete its
task regardless of anything, full stop. Force Run is the manual one, so it should never be
conditionally unavailable. `FlowCard._forceRun` (`flow_card.dart`) is unconditionally enabled now; the
confirmation dialog adapts its wording to whether there's actually a gate to bypass, a generic "runs
immediately, ignoring schedule/switch/limits" when there isn't. One honest caveat stayed: for
`entity-scan`/`entity-follow` specifically, a `no_work` gate means there's no queued entity or file to
act on at all — force can bypass every *condition* but can't invent input that doesn't exist — so the
dialog says so up front instead of the button silently doing nothing.

**Fourth round: two real bugs, both in `wait_until`, both from the same root cause — force_run and
the countdown ring only ever interacted with the gate, never with the wait itself.**

1. **Force Run silently did nothing on Follow after repeated tries, but worked on Scrape.**
   `force_run` was only ever consumed at the *top* of each trigger loop's outer `while`, never inside
   `wait_until`'s own tick loop. Press it while a flow is mid-wait and the command sits queued,
   unread, until that `wait_until` call returns on its own — for Scrape that's usually the 10s
   `SCRAPE_BUFFER`, easy to miss; for Follow it's `FOLLOW_WAIT`, up to 1200s. Every attempt you made
   landed during that long wait, so nothing visibly happened. `wait_until` now peeks (`_pending`, not
   `_consume` — same reasoning as the `wait_day_change` peek above) for a queued `force_run` every
   tick and wakes early, returning `"force_run"`; the trigger loop's own `_consume` still has to see
   it afterward to actually bypass the gate. This was latent for every flow, not Follow-specific —
   Ingest's 600s `INGEST_POLL_WAIT` had the same exposure, just less likely to be caught mid-wait in
   testing so far.
2. **Every countdown ring reset to a full circle every ~`TICK` seconds (default 5).** `wait_until`
   recomputed `deadline = datetime.now() + timedelta(seconds=target - elapsed)` from scratch on every
   tick. Mathematically that lands within a few milliseconds of the same instant each time — but
   never *exactly* the same `DateTime`, and the Flutter side's countdown-ring baseline
   (`FlowsController._deadlineObservedAt`) resets whenever `next_trigger_at` changes at all, by exact
   equality. So a wait that hadn't actually been re-targeted still looked re-targeted every tick,
   snapping the ring back to full. `deadline` is now a stable value held across ticks, only
   recomputed when `Config.get(key)` actually changes — an untouched wait now broadcasts the
   byte-identical instant every time, so nothing changes client-side until something real does.
   CP 3.2's original "re-targets within one TICK" behavior for an actual edit is unaffected (verified
   in isolation — see below), and this is also strictly better for `flows.state` traffic, since
   `SchedulerMirror.broadcast_if_changed()` (D27) was re-broadcasting on that same tick-boundary
   jitter for every waiting flow, every ~5s, whether anything real had changed or not.

**Verified in isolation, same technique as every round before this** (`Prefect.__new__`, no
Telegram/DB/device/Instagram calls): a pending `force_run` wakes `wait_until` early without consuming
it; `next_trigger_at` stays identical across ticks when the target is unchanged; an edit mid-wait
still re-targets the deadline correctly. One methodology note for whoever runs this script again:
by this point `config.env` has real explicit values for `TICK`/`FOLLOW_WAIT`/etc (you'd exercised the
new Timings tab), so overriding `Config._DEFAULTS["TICK"]` in the test no longer has any effect —
the file value wins, same as production. The tests still pass correctly, just slower (real 5s
ticks instead of the intended fake ones) — not a bug, just worth knowing next time.

**Fifth round: optimistic UI feedback for command buttons.** Even with the bug-1 fix above, there's an
unavoidable real gap between a command being queued and its effect being visible — the worker still
has to pick up the run, and the card only updates on the next `flows.state` broadcast. Long enough
that a second click was tempting. `flows_controller.dart` gained `PendingCommandNotifier`
(`pendingCommandProvider`): `FlowsController.sendCommand` marks the flow pending *before* the POST
resolves, capturing its current `phase`/`gate.reason` as a baseline. A flow clears as soon as a
`flows.state` snapshot shows that baseline actually changed (real confirmation, not just "a broadcast
happened" — the signature that gates a broadcast, D27, is global across all five flows, so an
unrelated flow changing must not clear this one), or after a fixed 8s timeout regardless, checked by
elapsed time rather than requiring another event, so it self-heals if the agent goes quiet mid-flight.
`FlowCard` swaps the Run now/Skip wait/Force run buttons for a small spinner + "Command sent…" in that
window — same footprint, no layout jump, and both buttons are unreachable for a second click since
neither renders at all while pending.

---

## 2026-07-31 — Phase 3 implementation session (closing the CP 3.4 gap, real heartbeats)

### D28 · `gate` is set once by the caller; `wait_until` only ever touches `phase`/`next_trigger_at`

**Chosen:** `Prefect` gained `self.flow_state: dict[str, dict]` (no lock — single event loop,
each trigger loop only ever writes its own key, unlike `ManagedService`'s cross-thread need for
`RLock`, D9) and `_set_state(flow, **fields)`, a merge-update. Every trigger loop now sets
`gate` (via a `_gate(ok, reason, detail)` helper) at the exact point it decides whether it's about
to trigger or skip — `backpressure` for scrape with the same `"scraped+follow_queued = N ≥
FOLLOW×F = M"` detail string ARCHITECTURE §4.3 illustrates, `day_limit` for the three day-capped
flows (set inside `wait_day_change`, which now takes an optional `flow` argument), `no_work` for
ingest/classify/scan/follow when their respective queue is empty. `wait_until` (D25) was extended
to set `phase="waiting"` and a recomputed `next_trigger_at` every tick, but **deliberately never
touches `gate`** — the caller's gate reason has to keep reading true for the whole wait that
follows it, not get clobbered back to "ok" the instant the sleep starts. `heartbeat_loop()` (2s,
`Prefect.serve()`) reads `flow_state`, layers in `switch` (`Deployment.switch()`), `today`
(flow-specific: scan gets three sub-counters against `PROFILES`/`REELS`/`POSTS`, scrape/follow get
one each, ingest/classify get `None` — they have no daily cap), and `last_run` (from
`Deployment.flow_run`, `getattr`-defensive since a fresh process has none yet), then calls
`AgentClient.heartbeat()` per flow.

**Verified cross-process**, not just in-process: a throwaway agent instance (`build_specs=[]`,
same pattern `test_scheduler.py`/`test_ui_contract.py` use) spun up on a spare port, and a real
`AgentClient` from the `Insta-Automate` venv (a genuinely separate Python environment — these are
two different `uv` projects, so this could not be one in-process test) posted a realistic §4.3
block against it. `GET /api/scheduler` on the throwaway agent read back the exact gate reason and
detail string, `online: true`. This is the first time data has actually crossed the pod→agent
boundary this phase — CP 3.3 only proved failures swallow correctly, never a real payload landing.
Also verified: a gate set before `wait_until` survives every tick of the wait unchanged.

**Rejected:** having `wait_until` accept the gate as a parameter and set it itself — would force
every call site to pass the *same* gate value it already just decided, for no benefit over setting
it directly; the split (caller decides *why*, `wait_until` only tracks *when*) is what let `gate`
survive across the wait without extra plumbing.

**Why:** this is what CP 3.4 (D27) explicitly left open — a real heartbeat loop was needed before
CP 3.5's Flows UI would have anything true to render.

**How to apply:** command handling is still not wired — `heartbeat_loop()` logs a warning if the
agent ever returns queued commands, but nothing acts on them. That's explicitly CP 3.5's job (D27's
open item), and needs a hook in `wait_until`'s tick loop to check for and short-circuit on a
queued command, returning something other than `"elapsed"`.

---

## 2026-07-31 — Phase 3 implementation session (CP 3.4, scheduler mirror in the agent)

### D27 · `flows.state` publishes the full snapshot on change; staleness needs its own watchdog

**Chosen:** `SchedulerMirror` (`ia_agent/scheduler.py`) — an `RLock`-guarded in-memory store, one
state block per flow, reusing `ManagedService`'s exact locking idiom (D9) rather than inventing a
new one. `heartbeat(state)` stores the block and drains that flow's queued commands in the same
call; `queue_command(flow, command)` is the write side, exposed at
`POST /api/scheduler/{flow}/command` with the six command names (§4.4) validated at the API layer,
400 on anything else. `flows.state` broadcasts the **whole snapshot** (`online`, `last_heartbeat_at`,
every flow's block) on every signature change, not a per-flow delta — mirroring how
`services.status` publishes one *complete* service status per change rather than a diff, which
means a client that missed some broadcasts is never stuck merging partial updates; it just has a
stale full picture until the next one arrives, and `GET /api/scheduler` gets it unstuck immediately.
Staleness (`STALE_AFTER = 15.0`s → `online: false`) needed a **watchdog task** (`WATCHDOG_TICK =
3.0`s) distinct from the heartbeat handler's own immediate broadcast-on-POST, because nothing
about a heartbeat *not* arriving would otherwise trigger a re-check — the supervisor's tick loop
has an equivalent structural role (it re-probes services on its own schedule; a service doesn't
have to tell the supervisor it died).

**Verified:** `agent/tests/test_scheduler.py`, 24/24 — pure store logic (command scoping per flow,
staleness flip, signature-gated broadcast) plus a live REST+WS round trip against a throwaway
`create_app()` instance on a separate port, with `build_specs` monkeypatched to `[]` exactly like
`test_ui_contract.py` so this test's own `Supervisor` never touches the three real services a
production agent may already be supervising. All five existing suites still pass unchanged
(71/71, 32/32, 49/49, 26/26, 20/20).

**Rejected:** per-flow delta broadcasts on `flows.state` — would need the client to merge partial
updates into a local model and handle the "I connected mid-session and have no baseline" case
itself; a full snapshot on every change sidesteps both, at the cost of a slightly larger payload
five small JSON blocks is not a size problem worth solving yet. Also rejected: giving `flows.state`
a `seq`-numbered replay ring like `services.logs.<name>` — that ring exists because a **log** is a
delta stream where a gap is a real loss (D18); a full-snapshot channel has no gap to lose, `GET
/api/scheduler` already *is* the replay.

**Why:** CP 3.4 is marked 🟢 (this repo only) in the plan — deliberately **not** wiring
`Prefect.serve()` to send real heartbeats, which stays open. An earlier note in D26 said CP 3.4
would include that pipeline-side wiring; that was wrong, corrected here. `SchedulerMirror` is
therefore verified against synthetic heartbeats only — nothing in `Insta-Automate` calls
`AgentClient.heartbeat()` yet, so `/api/scheduler` on the real running agent reads `online: false`
until that gap closes.

**How to apply:** the next piece of work needing this is either its own small checkpoint or folds
into CP 3.5 (Flows UI needs real data to render against) — add a `heartbeat_loop()` to
`Prefect.serve()` that builds the §4.3 block per flow (phase from `wait_until`'s state, gate from
each `limit_reached`/backpressure check, `today` from `Scan`/`Scrape`/`Follow.fetch()`, `last_run`
from `Deployment.flow_run`) and calls `AgentClient.heartbeat()` on it every ~2s, draining returned
commands into whatever `wait_until` (D25) checks to stop being `"elapsed"`-only.

---

## 2026-07-31 — Phase 3 implementation session (CP 3.3, agent client in the pod)

### D26 · `IA_AGENT_URL` stays a live `Config` key; only `IA_AGENT_TOKEN` moves to `vars.py`

**Chosen:** `controllers/agent.py`'s `AgentClient` has three methods — `heartbeat(state)`,
`emit(event)`, `notify(msg, ...)` — each POSTing to the agent and swallowing every exception,
returning the documented empty/false value on any failure (`[]`, `None`, `False`). The base URL is
read fresh on every call via `Config.get("IA_AGENT_URL")` (already a live `Config` key since CP
3.1, defaulting to `http://172.19.16.1:8787`), not a new `vars.py` entry — it changes with no pod
restart, same as every other `config.env` key, which is strictly better than an env var for
something that isn't a secret. `IA_AGENT_TOKEN` **is** new in `vars.py` (`getenv`-only, no
`config.env` fallback), because `config.env` is Syncthing-replicated to the phone (§4 intro) — a
bearer token has no business in a file that leaves the machine. `httpx` is now a direct dependency
(was only transitive, via `prefect`) since this repo imports it directly for the first time.

**Verified:** against a genuinely unreachable port (connection refused) — `heartbeat` → `[]`,
`emit` → `None`, `notify` → `False`, no exception escapes. Then against the real running `ia-agent`
on this machine, whose `/api/scheduler/heartbeat` and `/api/notify` don't exist yet (CP 3.4 and CP
6.1 build them) — both 404 and both still swallow cleanly, proving the failure path works
end-to-end against a real server, not just a closed socket.

**Rejected:** the ARCHITECTURE §8 cross-repo table's original sketch of putting both
`IA_AGENT_URL` and `IA_AGENT_TOKEN` in `vars.py` — written before CP 3.1 existed and before
`IA_AGENT_URL` was already a `Config` key. Doubling it into `vars.py` too would create two sources
of truth for the same value. §8 corrected in the same commit.

**Why:** the whole point of Phase 1 and Phase 3 is that `config.env` edits apply live; an env-var
`IA_AGENT_URL` would silently reintroduce a "needs a pod restart" exception to that rule for no
reason — a URL isn't sensitive the way a bearer token is.

**How to apply:** CP 3.4 builds the receiving `/api/scheduler/heartbeat` endpoint agent-side —
*correction, recorded when CP 3.4 landed:* it does **not** also wire `Prefect.serve()` to call
`AgentClient.heartbeat()`; that pipeline-side loop is still open, see D27. CP 4.2/4.3 wire `emit()`
into the flow task instrumentation points. CP 6.1/6.2 build `/api/notify` and the `Notifier` facade
that calls `AgentClient.notify()`. None of that requires touching `agent.py` itself unless the
payload shapes change.

---

## 2026-07-31 — Phase 3 implementation session (CP 3.2, config-driven scheduler)

### D25 · `wait_until` takes a config key, not a resolved seconds value, and gates `continue`

**Chosen:** `Prefect.wait_until(self, flow: str, key: str) -> str` — every hardcoded
`wait`/`buffer`/`sleep` in `controllers/prefect.py`'s five trigger loops now calls it with the
matching `Config` key (`INGEST_POLL_WAIT`, `CLASSIFY_POLL_WAIT`, `SCAN_WAIT`/`SCAN_POLL_WAIT`,
`SCRAPE_WAIT`/`SCRAPE_BUFFER`, `FOLLOW_WAIT`/`FOLLOW_BUFFER`, `TG_KEEPALIVE_WAIT`), and
`wait_day_change` reads `DAY_CHANGE_POLL` the same way. It sleeps in `Config.get("TICK")`
increments, re-reading `Config.get(key)` on every tick — the loop condition itself
(`elapsed < (target := Config.get(key))`) is what lets an edited delay shorten or lengthen a wait
already in progress. `SCRAPE_BACKPRESSURE_FACTOR` replaces the hardcoded `* 3` in
`entity_scrape_trigger`'s gate. The three day-limited loops (`entity_scan_trigger`,
`entity_scrape_trigger`, `entity_follow_trigger`) now `continue` immediately after
`wait_day_change()` returns, so the next iteration re-fetches `Scan`/`Scrape`/`Follow` fresh and
re-evaluates the gate before doing anything else, rather than falling through into that same
iteration's trigger logic on the pre-rollover object.

**Rejected:** `wait_until(self, flow: str, seconds: float)` as ARCHITECTURE §4.2 originally
sketched it — a resolved `float` is a snapshot; re-reading a snapshot re-reads nothing. Only
passing the *key* lets each tick go back to `config.env` itself. Also rejected: publishing a
countdown and checking for `run_now`/`skip_wait` commands inside `wait_until` now — no command
queue exists to check yet (that's CP 3.3's `AgentClient` and CP 3.4's heartbeat endpoint), so
`wait_until` always returns `"elapsed"` for now rather than a half-built command-check against
nothing. ARCHITECTURE.md §4.2 updated to match the real signature and note what's still missing.

**Why:** the plan's own CP 3.2 bullets ask for both "re-reads config" (needs the key) and
"SCAN_WAIT cooldown, default 0 = today's behaviour, no-op until set" — verified: `SCAN_WAIT=0`
makes `elapsed < target` false on the first check, so the wait returns immediately, identical to
today's absence of a scan cooldown.

**How to apply:** CP 3.3/3.4 extend `wait_until`, they don't replace it — add a command-check hook
(e.g. drain a queue `Prefect` owns) that short-circuits the `while elapsed < target` loop and
returns a reason other than `"elapsed"`, and a countdown publish call inside the same loop body.
Don't reintroduce a `seconds` parameter anywhere in this path.

---

## 2026-07-31 — Phase 3 implementation session (CP 3.1, typed live config)

### D24 · `Limit` is generalised into `Config` by aliasing, not renaming call sites

**Chosen:** `insta_automate.models.meta.Config` replaces `Limit` as the real class — typed
`get(key)` returning `int | float | bool | str`, inferred from the type of each key's own default
(bool checked before int, since `bool` is an `int` subclass in Python). `Limit = Config` at module
scope, so every existing call site (`scan.py`, `scrape.py`, `follow.py`, `entity_follow.py`,
`entity_scrape.py`, `controllers/prefect.py`, `tasks/ia.py`) keeps importing and calling `Limit`
unchanged. `_DEFAULTS` now carries every key from ARCHITECTURE §4.1 — the nine existing limits plus
eleven trigger timings, two gates (`SCRAPE_BACKPRESSURE_FACTOR`, `SCAN_LIST`), and two
control-center wiring keys (`IA_AGENT_URL`, `NOTIFY_POLICY`) — all absent from `config.env` today
and resolving to their coded defaults with no error, exactly as designed: CP 3.2 is what starts
reading them from the scheduler.

**Q3 answered: yes, `PROFILES`/`REELS`/`POSTS` are genuinely the live daily scan caps.**
`Scan.limit_reached` (`models/scan.py`) compares today's counts against `Limit.get(...)` for all
three, and `entity_scan_trigger` (`controllers/prefect.py:150-166`) pauses the trigger loop until
the next day when it fires. `config.env`'s own comment claimed the opposite — that these "only
bound Scan's schema" — which was simply wrong; corrected in the same commit.

**Rejected:** a parallel `Config` class living beside `Limit` with call sites migrated one by one —
unnecessary churn across five files for a rename that changes no behaviour, and the alias gets
identical type-checking (`Limit.get("FOLLOW")` still returns `int` for every key actually in use
today, since none of the new keys are read anywhere yet).

**Why:** the plan (`docs/PLAN.md` CP 3.1) specifies keeping `Limit` as an alias explicitly, and
`SCRAPE_BACKPRESSURE_FACTOR` in particular has no reader yet — CP 3.2 replaces the hardcoded `* 3`
in `entity_scrape_trigger` with it.

**How to apply:** any new trigger-timing or gate key CP 3.2 needs should be added to
`Config._DEFAULTS` with a same-typed default, not read directly from `config.env` — that's what
keeps an absent key from ever being an error.

---

## 2026-07-31 — Phase 2 implementation session (CP 2.6, services outlive the agent)

### D23 · The pty moves to a detached host, spawned through a launcher that exits immediately

**Chosen:** a new process, `services/host.py` (run as `python -m ia_agent.services.host <name>`),
owns the ConPTY that used to live in the agent. It never has the agent as its *live* parent: the
agent spawns `services/host_launcher.py`, which starts the host and exits within milliseconds, so
by the time anything tree-kills the agent, the host's `ppid` points at an already-dead launcher and
is unreachable from that walk — the same mechanism D22's own experiment measured. Two channels
cross the process boundary, kept deliberately separate: the raw output stream
(`%LOCALAPPDATA%\ia-agent\run\<name>.stream`, truncated fresh per spawn, tailed into the existing
`LogRing` so the `seq`/`?since=` contract, D18, does not change) and resize, over a Windows named
pipe (`multiprocessing.connection`, stdlib only) — the one thing a file cannot carry. A third file,
`<name>.json`, extends the old PID-file schema with `host_pid`/`host_create_time` and `exit_code`:
once the exit-immediately launcher is gone, the agent has no OS-level wait() relationship to the
host, so this file is the *only* way it learns the exit code.

Host takes its spawn parameters (cmd/cwd/env/rows/cols) from a small `<name>.spawn.json` the
supervisor writes just before launching it, rather than looking a `ServiceSpec` up by name in the
registry. Host needs none of `ServiceSpec`'s probe/self-test callables — only the supervisor probes
and tests — and taking them as data keeps host usable for whatever a caller wants run in a pty,
which is what let the test suite spawn its fake services through the exact same path as the three
real ones instead of a special case.

**Rejected:** a job object granting the host `KILL_ON_JOB_CLOSE`-style protection (unnecessary —
Windows does not kill a child when its immediate parent exits, it only orphans it, so plain process-
tree topology is enough); resolving the host's spec via `registry.build_specs()` by name (would have
made the test suite's dummy services unspawnable through the real path, which is exactly the
structural gap D22 says let the old adoption test miss the bug); and keeping the resize path on the
same file as output (a file has no way to signal "this pty's grid changed" to a process that already
has it open for writing).

**Why:** measured, cross-process this time. `agent/tests/fake_agent_process.py` builds a real
`Supervisor` in its own process, spawns a service through the real host path, and the outer test
(`test_supervisor.py` §14) `taskkill /F`s and separately `taskkill /F /T`s that process — the host
and the service it owns survive both, with the same pids, and a fresh `Supervisor.adopt()` recovers
`terminal_available: true` with the real output intact. This is the test D22 says the old two-
Supervisors-in-one-process adoption test structurally could not be, because in that shape the pty
handles never actually closed. Verified live on this machine too: took all three real services under
supervision, killed `ia-agent.exe` outright, and vl-server/wsl-bridge came back `adopted` on the
same pids with zero restarts and their real startup logs (including vl-server's model-load banner
from *before* the kill) replayed into the terminal.

**Known interaction, not a bug:** the job object in `ia_agent_launcher.pyw` (D21) has no breakaway
flags, so the host — like everything else the agent spawns — is a member of it. That job's handle
only closes when the launcher itself ends (`schtasks /End`, or the launcher dying), never on a plain
agent crash or restart, which is the case this checkpoint and D21's backoff loop both cover. So
`schtasks /End` remains "genuinely stop everything" (already the documented behaviour, D21) and will
also stop supervised services now; a routine agent crash or restart will not.

**Also observed, not caused by this change:** adb's `-a nodaemon server start` forked a detached
`adb -L tcp:5037 fork-server server` grandchild that escaped the host's process entirely, twice,
independent of anything this checkpoint did to the agent. Both the wrapper and its host ended up
gone while the fork kept the port, which the agent correctly reports as `external` (D11 already
anticipates exactly this shape) rather than silently losing track of it. Not a CP 2.6 regression —
`registry.py`'s adb spec is untouched — and not this checkpoint's to fix.

**Cost:** two more files under `%LOCALAPPDATA%\ia-agent\run\` per service (`.spawn.json`,
`.stream`, alongside the richer `.json`), one more stdlib IPC surface to reason about, and adoption
now starts a tailer thread instead of doing nothing — a small amount of always-on complexity in
exchange for D10 finally being true.

---

## 2026-07-31 — Phase 2 implementation session (CP 2.5, agent autostart)

### D22 · Supervised services die with the agent today, and the fix is CP 2.6
**Chosen:** ship CP 2.5 knowing that anything the agent supervises dies when the agent dies, and
close the hole in its own checkpoint (CP 2.6) with a detached host process that owns the
pseudo-console. Until then the loop is: agent dies → its services die → the launcher restarts the
agent → the agent restarts them from their `autostart` switches. Seconds of downtime, self-healing,
and no flow survives it.
**Rejected:** accepting it permanently (every agent restart across Phases 3–7 would take adb,
vl-server and wsl-bridge with it, and any flow running at that moment); and building the host
inside CP 2.5 (a supervisor rework plus three test suites, with the reboot test hostage to it).
**Why:** measured, not reasoned. A service spawned into a ConPTY dies whenever the agent's handles
close — on a clean `sys.exit`, on `taskkill /F`, and on `taskkill /F /T` alike. So D10's promise
("supervised processes outlive the agent; PID files are what the next run adopts") has been false
since services moved into pseudo-consoles in CP 2.1, and the adoption tests never caught it because
they build two `Supervisor`s inside one process, where the pty handles never close. The fix is also
measured: with the pty owned by a small detached host, the service survived a clean exit, a `/F`
kill, and a `/F /T` tree-kill (that last one only when the host is orphaned through a launcher, since
a tree walk otherwise reaches it), and its raw output kept appending to a file across the kill —
which is what a replay needs.
**Cost:** D10 is aspirational until CP 2.6, and CP 2.4's "restart the agent mid-scrape" claim does
not hold yet. The plan says so at both places.

### D21 · The launcher heals the agent; Task Scheduler does not
**Chosen:** `agent/scripts/ia_agent_launcher.pyw` starts the agent, waits for it, and restarts it on
any non-zero exit with 5 s → 300 s backoff (reset once the agent has been up two minutes), stopping
only on a clean exit or when `%LOCALAPPDATA%\ia-agent\stop-launcher` exists. The task's logon trigger
repeats every 10 minutes with `MultipleInstancesPolicy: IgnoreNew` as the outer net for the launcher
itself dying. The launcher holds the agent in a job object with `KILL_ON_JOB_CLOSE`.
**Rejected:** `RestartOnFailure`, which is what a logon task was chosen for in the first place; and a
launcher that spawns and exits, which would leave Task Scheduler with nothing to track.
**Why:** all three parts are measurements. `RestartOnFailure` (`PT1M`, count 3) did **not** restart a
killed agent — the task recorded `Last Result: 1`, went to `Ready`, and sat there for three minutes.
The repetition trigger did: a killed task was running again 55 s later. And `schtasks /End` killed
only the launcher, leaving the agent serving on 8787 as an orphan whose parent was gone — so the
documented way to stop the agent left something holding the port the next run needs. The job object
closes that: when the launcher dies, by `/End` or otherwise, the agent and its uv trampolines go
with it.
**Cost:** a supervisor of the supervisor, in a file that runs on the base interpreter and therefore
cannot import anything from the agent. `schtasks /End` is now genuinely "stop everything", which also
means it is not a way to restart the agent alone.

### D20 · The logon task runs a GUI-subsystem interpreter, never the agent directly
**Chosen:** the task's action is the **base** interpreter's `pythonw.exe` (`sys.base_prefix`, PE
subsystem 2) against the launcher `.pyw`, which then starts `ia-agent.exe` with `CREATE_NO_WINDOW`
and redirects its output to `%LOCALAPPDATA%\ia-agent\logs\startup.log`.
**Rejected:** `ia-agent.exe` with the task's `Hidden` setting (that flag hides the task in the Task
Scheduler UI, not the window); the venv's `pythonw.exe`; and `CREATE_NO_WINDOW` combined with
`DETACHED_PROCESS`.
**Why:** Task Scheduler exposes no window style, so what matters is the subsystem of the exe it
starts. Measured under a real interactive logon task: `python.exe` showed a visible console for its
whole run, and so did the venv's `pythonw.exe` — it is a uv trampoline that re-execs the console
interpreter, and the pid that appeared on screen was not the pid the task started (the same
trampoline shape as D11). The base `pythonw.exe` reported `GetConsoleWindow() == 0` and no window was
visible from outside. `CREATE_NO_WINDOW` is passed alone because Windows ignores it when
`DETACHED_PROCESS` or `CREATE_NEW_CONSOLE` is also set — the first attempt combined them and put a
console window on screen, which is the exact thing this checkpoint exists to remove.
**Cost:** the task depends on a path under `%APPDATA%\uv\python\…` that a uv toolchain upgrade can
move, so `startup.py status` re-checks it and `install` must be re-run if it changes. The agent's own
stdout is only readable in `startup.log`.

---

## 2026-07-31 — Phase 2 implementation session (CP 2.4, Services UI)

### D19 · The panels above the terminal are capped; the terminal keeps a floor
**Chosen:** the detail pane is `LayoutBuilder` → a `ConstrainedBox(maxHeight: available − 220 − 16)`
holding a `SingleChildScrollView` of the header/stats/switches/test panels, then `Expanded` for the
terminal. Layout regressions are caught by `app/test/services_layout_test.dart`, which renders the
widgets at three pane widths with deliberately awkward values and fails on the first pixel over.
**Rejected:** the plain `Column` + `Expanded(terminal)` this shipped with (overflowed by 199 px at
the minimum window); scrolling the whole pane with the terminal at a guessed fraction of the
viewport (leaves dead space under the terminal in a tall window); and `SliverFillRemaining`, which
collapses the terminal to nothing exactly when the panels are the ones overflowing.
**Why:** at the 1024 px minimum window the pane is ~550 wide, the stat chips wrap onto four rows and
every card's text wraps with them — the panels genuinely want more height than the window has, so
`Expanded` was being handed negative space. Capping them with a *maximum* rather than a share is
what keeps both ends honest: cramped, they scroll and the terminal still gets 220 px; roomy, they
take their natural height and the terminal gets every remaining pixel with no gap.
**Cost:** two scroll regions in one pane at small sizes. Accepted because the terminal is the thing
you are watching, and it staying put while the panels scroll is the behaviour you want.
**Worth remembering:** this was found because the user's screenshot showed a 43 px overflow in the
metrics row and the test written to chase it found three more. Overflow is a *paint-time* error —
`flutter analyze` cannot see it, and neither can any agent-side test. The first version of that test
used 560 and 1400 px panes and reproduced none of it: the reported bug needs ~1250 px, the width a
maximized 1920 window leaves. Test at the size the real screen produces, not at round numbers.


### D18 · The agent's ring is the terminal's source of truth; the client dedupes by `seq`
**Chosen:** the pane replays `GET /services/{name}/logs` on mount, holds back any live chunks that
arrive while that request is in flight, merges both by sequence number, and drops anything it has
already rendered. A dropped WebSocket re-replays from `?since=<last rendered>`. Navigating away and
back rebuilds the emulator from the server rather than keeping it alive off-screen.
**Rejected:** trusting the live stream to continue exactly where the replay stopped, and keeping the
terminal widget alive across navigation to preserve scrollback.
**Why:** measured, not assumed — the ring is written by the reader thread the instant the process
prints, while the WS batch for those same chunks is published on the next supervisor tick, up to
250 ms later. So replay-then-subscribe reliably delivers the same chunks twice; a first attempt at
`test_ui_contract.py` asserted the opposite and failed against correct behaviour. Overlap is
harmless and a gap is not, so the client absorbs the overlap and the test now pins both properties
(no gap, full coverage of every sequence number).
**Cost:** re-opening the Services tab re-fetches up to 512 KB of scrollback. Cheap on localhost, and
it means there is exactly one copy of the truth.

### D17 · A pane with nothing to render explains itself instead of rendering the ring
**Chosen:** `external` and `adopted` services show a card naming why there is no output and what to
do about it (take over / restart), never a terminal. A *stopped* service is treated differently: its
ring is genuine output, so it keeps the terminal with a banner saying this is history and, where
there is one, the exit code.
**Rejected:** gating purely on `terminal_available`, which is what the endpoint offers.
**Why:** an external service's ring is not empty — it holds exactly one chunk, the agent's own dim
note that the port was taken by someone else. Rendering it would produce a "terminal" whose entire
contents are one line about itself. That is the state all three real services are in today, so it is
the first thing the screen shows. Meanwhile `terminal_available` is also false for a supervised
service that exited, where the output is exactly what you want to read — which is the whole point of
being able to switch self-heal off (D12).
**Cost:** one more piece of client-side state to keep in step with the origin enum; the rule is
"detached (external/adopted) → explain; otherwise render whatever the ring has".

### D16 · The dependency panel is the Services screen's second tab
**Chosen:** Services is two tabs — *Supervised* (the three services, master–detail with the
terminal) and *Dependencies* (CP 2.3's ten read-only checks).
**Rejected:** waiting for the Overview screen, which ARCHITECTURE §9 earmarks for a dependency
strip.
**Why:** CP 2.3 shipped `GET /api/dependencies` with no UI, and Overview is not in Phase 2 — the
panel would have stayed invisible until Phase 7. Both tabs answer one question about one machine
("is this laptop able to run the pipeline?"), and the split is honest about the difference that
matters: one tab has buttons because the agent owns those processes, the other has none because it
does not.
**Cost:** Overview will later show a condensed version of the same data; this stays the detailed
view rather than being moved.

---

## 2026-07-31 — Phase 2 implementation session (CP 2.1, revised after review)

### D15 · Services are spawned into a ConPTY, and their output is kept verbatim
**Chosen:** `PtyProcess.spawn` (pywinpty) instead of `subprocess.Popen`, with the raw stream stored
as chunks — ANSI escapes, cursor moves and carriage returns intact — and rendered in the app with a
real terminal emulator (`xterm.dart`). The rotating file on disk is the only flattened copy
(`render_plain` strips escapes and keeps the last carriage-return frame).
**Rejected:** pipes with line-oriented storage, which is what CP 2.1 originally shipped.
**Why:** the requirement is a terminal, not a log list, and these panes replace `wt.exe` tabs — so
they have to show what those tabs showed. Measured on this machine: under a pipe the child sees
`isatty() == False` and suppresses colour; under ConPTY it reports `isatty: True` and emits
`\x1b[32m…` and `\rprogress 3/3` exactly as the terminal did. Line-oriented storage
(`line.rstrip("\r\n")`) destroys precisely the bytes a terminal needs — a progress bar is one line
rewritten a thousand times, and splitting on newlines turns it into nothing.
**Cost:** a pseudo-console has one stream, so stdout and stderr merge and can no longer be tagged
separately. Terminal size must be plumbed from the UI to the process (`POST /services/{name}/resize`),
because otherwise anything drawing to the full width wraps at the wrong column. Scrollback is
bounded by bytes (512 KB), not lines, since a line count no longer bounds memory.

### D14 · The agent owns restart; the services' own restart loops are switched off
**Chosen:** one supervisor, at the agent. `start_vl_server.py` is launched with its existing
`--no-autorestart` flag, and adb runs as `-a nodaemon server start` rather than `-a start-server`.
**Rejected:** leaving each service to heal itself.
**Why:** the restart logic was in the wrong place and covered one service of four. Measured before
changing anything: only `start_vl_server.py` retried; wsl-bridge had none; and `adb -a start-server`
forks so the shortcut's tab exits immediately and *nothing* supervises adb at all. Nested
supervisors also fight — the launcher would resurrect llama-server underneath a stop or takeover
(D11) — and a restart count printed to an unread terminal tab is information destroyed at the
moment it is produced, which is exactly the diagnostic needed for "vl-server sometimes crashes".
**Cost:** the flag must stay in the spec; if someone launches `start_vl_server.py` by hand it will
still self-restart and be detected as `external` rather than supervised. No change was needed in the
`Insta-Automate` repo — the flag already existed.

### D13 · `ollama serve` is dropped, not supervised
**Chosen:** the agent supervises three services; `ollama serve` leaves the startup set entirely.
**Rejected:** carrying it over as a fourth supervised service.
**Why:** nothing in the pipeline talks to 11434 — `vars.py` points at `VL_SERVER_URL` on 11500, and
`OLLAMA_URL` is defined but never read. `start_vl_server.py` needs Ollama *installed* (it resolves
the model blob out of `~/.ollama/models` and runs Ollama's bundled `llama-server.exe`), not serving.
`Ollama.lnk` is independently in the Startup folder, so the tab was redundant twice over.
**Cost:** if something outside Insta-Automate ever wants Ollama's own API, it is no longer started
by this path — the Startup shortcut still covers it.

### D12 · Service switches live in `services.json`, not `config.env`
**Chosen:** per-service `self_heal` and `autostart` persist to
`%LOCALAPPDATA%\ia-agent\services.json`, applied over the spec defaults at construction.
**Rejected:** adding them to `config.env` alongside the flow switches.
**Why:** `config.env` is IA_DIR-relative, Syncthing-replicated to the phone and read live by the
flows inside the pods. Which Windows processes *this machine* supervises is meaningless to a pod and
actively wrong to sync to a phone. The two files answer different questions: `config.env` is what
the pipeline does, `services.json` is how this host runs it.
**Cost:** a second settings file, and the Services UI cannot reuse the config screen's plumbing.

### Self-heal semantics (implements the requirement, no separate decision)
`RestartPolicy` (always / on-failure / never) collapsed into one `self_heal` boolean, because that
is what was actually asked for. On: restart on exit *whatever the code*, since none of these
services is meant to return, and also restart a process that stays alive while its probe fails for
`unhealthy_grace` (60 s) — wedging is the failure a crash-only policy never notices. Off: leave it
`failed` with its exit code and terminal intact. Turning the switch back on rescues an
already-failed service rather than waiting for the next crash to prove the switch works.

---

## 2026-07-31 — Phase 2 implementation session (CP 2.1)

### D11 · Takeover targets the *service root*, not the process holding the port
**Chosen:** when a port is held by a process the agent did not start, `_service_root()` walks up
the parent chain from the socket owner and stops at the first session host (`WindowsTerminal.exe`,
`explorer.exe`, `powershell.exe`, …), at the agent's own lineage, or after six hops. Takeover kills
that root's whole tree. The status reports both: `external` is what would be killed, `port_owner`
is what holds the socket.
**Rejected:** killing the port owner alone.
**Why:** `Insta-Automate/scripts/start_vl_server.py` runs its own restart loop around
`llama-server.exe` (5 s backoff, doubling). Killing only llama-server would have the launcher bring
it straight back and fight the agent's takeover. Verified live: the resolution walks
`llama-server.exe (23276) → python start_vl_server.py (23112)` and stops at `WindowsTerminal.exe`
(20840, the `wt.exe` shortcut CP 2.5 retires). `psutil.parent()` compares creation times, so a
recycled PPID cannot redirect the walk into an unrelated process.
**Cost:** a denylist of host process names that needs a new entry if the services are ever launched
from a different shell. The agent's own lineage check is what stops the walk from killing the agent.

### D10 · Agent shutdown leaves supervised processes running
**Chosen:** `Supervisor.shutdown()` cancels the tick loop and returns; it never stops the services.
PID files (with `create_time` as a PID-reuse guard) persist, and the next agent run adopts them,
flagging `stdout_available: false` because the pipes belonged to the previous process.
**Rejected:** stopping supervised services on agent exit (systemd-style ownership).
**Why:** D1's stated cost was that the agent "needs adoption logic so it can restart without
killing a running scrape". Tying service lifetime to agent lifetime would make every agent restart
a pipeline outage — the opposite of what this project is for. Stopping a service stays an explicit
operator action.
**Cost:** a service can outlive the agent that started it, so a stale PID file is possible; the
`create_time` guard makes a stale file discardable rather than dangerous.
**Measured limit, found 2026-07-31 by doing it:** this holds for a *graceful* exit only. Killing the
agent's **process tree** takes every supervised service with it — all three were taken over during
the CP 2.4 test, and killing the agent that way left the machine with no adb, no vl-server and no
wsl-bridge (restarted by hand; PID files were left behind, which is exactly the stale-file case the
`create_time` guard exists for). Not yet measured: whether killing the agent process *alone* (Task
Manager's "End task") does the same, which it plausibly does since each service is attached to a
pseudo-console the agent owns. **CP 2.5 has to answer that before it turns on restart-on-failure**,
because a logon task that restarts a crashed agent would otherwise cycle all three services with it.

### D9 · Supervisor state is guarded by a per-service re-entrant lock
**Chosen:** every operator action (`start`/`stop`/`restart`/`takeover`) holds an `RLock`, and
`tick()` skips a round entirely if it cannot take that lock without blocking. `_spawn()` claims
`origin = SUPERVISED` *before* the blocking `Popen`, not after.
**Rejected:** relying on the GIL and short critical sections.
**Why:** found by the CP 2.1 end-to-end test, not by reading. The API offloads actions with
`asyncio.to_thread` so a slow kill cannot stall the probe loop — which means a tick on the event
loop ran while `start()` was still inside `Popen` on a worker thread. It saw `origin = NONE` with a
freshly-bound port, concluded the process the agent was itself starting belonged to somebody else,
and marked the service `external`. The test caught it as `stdout_available: false` after a
successful start.
**Cost:** the lock is held across the probe `await`, so an action can wait up to one probe timeout
(2 s) before it begins. Bounded, and on a worker thread, so nothing user-facing blocks.

---

## 2026-07-31 — Phase 1 implementation session (CP 1.4)

### D8 · `ENTITY_QUEUE` stays one shared list (answers Q1)
**Chosen:** keep the single `ENTITY_QUEUE` key driving both the scrape and follow priority. The
UI presents it as one priority list, not two.
**Rejected:** splitting into `SCRAPE_QUEUE` / `FOLLOW_QUEUE`.
**Why:** the key holds *entity names*, and `Queue.load_queue()` maps that ordering onto whichever
directory the instance was constructed with — `pref_queue = [self.directory / entry ...]`. The
scrape/follow distinction already comes from the folder, so the shared key is not an oversight:
an entity worth prioritising is worth prioritising at both stages. Splitting would add a second
list to keep in sync for no behavioural gain.
**Cost:** none to the flows (no change). The UI must explain the shared semantics, and must show
per-entity counts in *both* `scrape_queued` and `follow_queued` so the one list reads honestly.
**Noted while reading the code, not acted on:** `pref_queue` maps every listed name into the
directory without an existence check, so a queued entity with no folder at that stage still yields
a `Path` that does not exist. Harmless for ordering, but worth remembering if the flows ever
iterate the queue eagerly. Belongs to `Insta-Automate`, so it is feature-branch territory.

---

## 2026-07-31 — Phase 1 implementation session (CP 1.3)

### D7 · Open `config.env` by replicating the `code` shim, not by running `Code.exe`
**Chosen:** `FileOpener.openForEditing` resolves `code.cmd` on `PATH` to locate the install root,
then launches `Code.exe <cli.js> <path>` with `ELECTRON_RUN_AS_NODE=1` via `Process.start`
(detached), falling back to the shell association, then Notepad.
**Rejected:** `CreateProcess` on `Code.exe "<path>"` — this *silently does nothing*. It starts a
second Electron main process which exits without opening the file, while `CreateProcess` still
reports success, so the failure is invisible to the caller. Also rejected: `cmd /c code "<path>"`,
which re-introduces the console flash D5 exists to avoid.
**Why:** the *Open* button did nothing across two CP 1.3 test rounds. Reading `code.cmd` showed
the shim is not a thin wrapper around `Code.exe` at all — it runs the `cli.js` entry point under
`ELECTRON_RUN_AS_NODE`, and *that* is what hands a file to the running window. Verified by exit
code (`0`) before shipping. `Process.start` is safe here where D5 forbade it, because the flash D5
describes only affects console-subsystem binaries like `uv`/`python`; `Code.exe` is GUI-subsystem.
**Corrects an earlier claim in this entry:** the first version blamed `.env` having no file
association. That was wrong — measured directly, `ShellExecute('open')` on `config.env` returns
`42` (success) on this machine. The association was never the problem.
**Cost:** two path heuristics (`code.cmd` lives in `<install>\bin`; `cli.js` sits under
`resources\app\out`, possibly beneath a version-hash directory, so it is searched for rather than
assumed). The fallback chain covers a layout change.

---

## 2026-07-31 — Phase 1 implementation session (CP 1.1)

### D6 · `/ws` broadcasts every event to every client, no channel filtering yet
**Chosen:** the new `/ws` endpoint (`api/ws.py`, `events/bus.py`) sends every published event,
tagged `{channel, data}`, to every connected client. There is no client-side subscribe protocol.
**Rejected:** building ARCHITECTURE §3.2's full per-channel subscription + replay-cursor model now.
**Why:** `config.changed` is the only channel that exists so far, so subscription filtering has
nothing to filter yet. Building it against one channel risks guessing the wrong shape for the
eight others (`services.status`, `flow.events`, `library.changes`, ...) that show up in later
phases.
**Cost:** every connected client gets every event once more channels exist — revisit when a
second channel lands (Phase 2's `services.status` is the likely trigger) and add subscribe/
unsubscribe + replay then, not speculatively.

---

## 2026-07-31 — Phase 0 implementation session

### D5 · Launch ia-agent via raw Win32 `CreateProcess` with `CREATE_NO_WINDOW`
**Chosen:** the desktop app's *Start agent* action calls `package:win32`'s `CreateProcess`
directly over FFI, passing `CREATE_NO_WINDOW`, instead of `dart:io`'s `Process.start`.
**Rejected:** `Process.start(..., mode: ProcessStartMode.detached)` — `uv`/`python` are
console-subsystem executables, and `dart:io` never exposes Windows' `CREATE_NO_WINDOW` creation
flag, so a bare `Process.start` flashes a visible terminal window every time the button is
pressed.
**Why:** caught during CP 0.3 manual testing — clicking *Start agent* popped a console window,
which is exactly the `wt.exe`-shortcut experience this project exists to replace (see
EXPECTATION.md's no-compromise-on-UI/UX rule and CLAUDE.md §Rules #6).
**Cost:** two new Flutter dependencies (`win32`, `ffi`) and one raw-FFI call site
(`app/lib/core/agent_launcher.dart`) that has to track the `win32` package's API shape (pinned to
6.3.0's extension-type-based bindings at time of writing).

---

## 2026-07-30 — Planning session

### D4 · Desktop gets full curation parity
**Chosen:** the Windows app implements the image review workflow (entity grids, multi-select,
apply-to-next-stage, delete, queue ordering) that today only exists on the phone.
**Rejected:** observability-only, and read-only-viewer-first.
**Why:** the two human gates in the pipeline (`gender_valid → scrape_queued`,
`scraped → follow_queued`) are the pipeline's actual bottleneck, and reviewing 7,566 images on a
phone is the slow path. Doing it at the laptop also makes Syncthing latency irrelevant.
**Cost:** Phase 5 is a substantial phase; the grid must be virtualized and keyboard-driven from
the start.

### D3 · LAN WebSocket notifications with a Telegram backstop
**Chosen:** the phone holds a WebSocket to the agent via an Android foreground service and raises
local notifications; the agent answers `{delivered}` and the flow falls back to
`tl.bot.notify(...)` when nothing was listening.
**Rejected:** FCM (needs a Firebase project and routes metadata through Google) and
Telegram-stays-primary (keeps the delay and the context switch being designed away).
**Why:** the requirement was scoped to "when I'm on the same wifi". Keeping it local avoids a
cloud dependency entirely, and Telegram already works as the away-from-home path.
**Cost:** only works on the LAN, and Android shows a persistent foreground-service notification.

### D2 · Structured flow events, not log scraping
**Chosen:** add a failure-tolerant `emit()` beside the existing `log.info` calls at every
image-producing point, and have the agent cache image bytes the moment an event arrives. Backed
by a filesystem watcher for everything not covered by an event.
**Rejected:** parsing paths out of Prefect log messages with regex.
**Why:** `entity_classify` unlinks public profiles and moves the rest, and `entity_follow`
unlinks the image immediately after logging it. A log-scraping UI races those deletions and shows
holes. Events also carry verdicts, skip reasons with real numbers, and counters that the log
lines only partly contain.
**Cost:** a real diff in `Insta-Automate` (`tasks/ia.py`, `tasks/ollama.py`, the five flow
bodies), on a feature branch.

### D1 · Flutter UI + Python `ia-agent`, both in this repo
**Chosen:** a FastAPI agent at `agent/` becomes the single Windows startup entry, replacing the
`wt.exe adb … ; start_vl_server.py ; wsl-bridge.exe` shortcut. It supervises the three core
services, ingests flow events, and serves both the desktop app and the paired phone. The Flutter
app is a pure client.
**Rejected:** Flutter-only (services would die with the window, and the pods would lose their
notify endpoint whenever the UI is closed) and extending `wsl-bridge` (all the work would land in
an external repo, and wsl-bridge would stop being a supervisable core service by becoming the
supervisor).
**Why:** services must outlive the UI; the phone needs the same API the desktop uses; and Python
already owns every integration required (`adbutils`, `telethon`, `my_modules.*`, the Prefect
client).
**Cost:** two processes to keep alive instead of one; the agent needs adoption logic so it can
restart without killing a running scrape.

# Virtua 0.51.0 scroll correction boundaries

The application imports the React ESM entry (`virtua` → `lib/index.js`) from
`src/features/messages/ChannelTimeline.tsx`. Only that entry's element scroller,
store and `Virtualizer` (with its declaration file) are patched; CommonJS,
window scrolling, and other-framework exports are untouched.
Keep the dependency pinned to 0.51.0 and review the patch plus version-coupled
installed-bundle tests before upgrading or adding a different import.

## Fractional end offsets

Text layout can produce fractional row heights. WebKit can truncate an absolute
scroll offset before clamping it, leaving the final row partly outside the
viewport even when Virtua requests the end of the list. A focused notification
target then correctly remains unread under the full-row visibility policy.

The element driver rounds end-boundary targets upward before RTL normalization,
for both imperative scrolling and automatic resize compensation. The browser
clamps that target to its actual scroll range. Interior reading offsets remain
fractional, and the existing scheduling, focus and dwell rules are unchanged.
Installed-driver regressions cover both entry points and RTL; a browser regression
sets a fractional list height explicitly and requires the final row to be fully
visible without a pixel tolerance.

## Buffer while the scroll direction is frozen

Virtua renders `bufferSize` only ahead of the scroll direction, and updates that
direction only during native scrolling. A shift (prepended history) or imperative
scroll freezes it until the 150ms inferred idle. Continuous trackpad flicks can
keep it frozen: a downward flick after an upward prepend renders no rows below the
viewport, and React commits one frame behind, so the leading edge stays blank for
the rest of the gesture. The range therefore buffers both sides while the
direction is frozen, as it already does when idle. Native directional buffering
is unchanged, and the extra buffer is no larger than the idle buffer.

A shift otherwise counts every row resize as an anchoring correction. Rows wholly
below the viewport are excluded, so a newly buffered row there that resizes (a
video loading, say) cannot move the reading position. Rows above and in the
viewport, including prepended history, are still corrected.

In an isolated WKWebView over real channel history (images, video, live relay),
fast alternating flicks were measured per frame. In two instrumented runs, all 46
DOM-coverage gap frames moved downward while shift mode held an upward direction.
Stock showed 3–96 gap frames per run over ten runs; the patch showed none in six.
Short main-thread stalls and image decode dips remain.

## Failure and chosen boundary

In a system WKWebView, native momentum can overwrite an instant programmatic
scroll correction. An isolated reproduction adapted from
[WebKit 262287](https://bugs.webkit.org/show_bug.cgi?id=262287) sustains missing
pixels even after DOM geometry covers the viewport. The same failure reproduces
with the production ChannelTimeline and fixed messages when history is prepended.
This does not attribute every disappearing-content incident to this mechanism.

The previous Mac deferred-store/extent patch is **superseded**. A pause in native
momentum can outlast Virtua's 150ms inferred-idle timer: the deferred correction
then runs before native momentum actually ends, and the timeline stays blank.
One of two paused draft trials failed; this was timing-dependent, not a
universally failing sequence. Increasing an idle timeout is not the remedy.

Instead, at each **nonzero automatic correction** on Mac WebKit:

1. Temporarily set only the corrected overflow axis to `hidden !important`.
2. Apply Virtua's original relative correction or absolute edge target.
3. Restore the prior declaration value and priority in the next task.

This extends the mechanism already used by
[Virtua's iOS driver](https://github.com/inokawa/virtua/blob/0.51.0/src/core/driver.ts#L203-L248),
without changing the iOS branch. Overlapping interventions cancel/restore their
predecessor before capturing the original declaration. Disposal restores
immediately; an observably changed later declaration is not overwritten.

**Tradeoff:** a correction can stop the remaining trackpad coast. Several size
corrections can therefore reduce inertial travel more than one prepend. A fresh
gesture must continue to work; sustained real-history/media acceptance must assess
whether repeated braking is acceptable. No wheel ownership, permanent scrolling
CSS, forced layout, alternate store sizing, or new scroll scheduler is introduced.

The `overflow-y: hidden` frame also removes a classic, space-taking scrollbar.
Every scroller driven by the patched Virtualizer on Mac WebKit must therefore
keep a constant inline size across the toggle (`scrollbar-gutter: stable`, as
`.feed` in `src/features/messages/Messages.module.css` does). Otherwise the wider
content box re-wraps rows above the viewport, their new heights become the next
nonzero correction, and the interrupt feeds itself until the scroller oscillates
between two wrap widths.

The momentum-interruption predicate requires MacIntel and Apple vendor, excluding
Virtua's iOS detector (including desktop-mode iPad). Chrome/Firefox, non-Mac WebKit
and iOS keep existing momentum policy. Store/layout timing and imperative smooth/instant target calculation remain stock.
The cancellation boundary below retires superseded targets. Scheduler-driven
reveal/restore/bottom navigation is a
separate acceptance path, not implicitly repaired by the automatic-correction fix.
Native reveal controls showed one/two transient blank interior source frames
before immediate recovery, despite valid sampled DOM coverage. This remaining
imperative-path flicker is not the sustained automatic-correction failure; the
patch does not claim to fix it.
The stale source-map directive is removed because the generated map is unpatched.

## Newer reader input cancels retained navigation

Virtua retains imperative targets for late measurements for 150 ms. After a jump
to latest, new upward input could detach the reader, but a row measurement inside
that window replayed the old target and pulled them back down. The element driver
now invokes its existing cancellation closure on wheel, touchmove, keydown and
pointerdown, matching ChannelTimeline's reader-intent events. Capture listeners
retire the old command before a descendant handler can issue new navigation;
no input is prevented and automatic resize compensation is unchanged. Disposal
also cancels retained work and removes the listeners.

Installed-driver tests keep the clock inside the pending command's lifetime,
including a replay already queued as a microtask, and verify a fresh navigation
still responds to measurements. The browser navigation case exercises real wheel
input and late row growth, asserting position as well as arrival count. These are
not native momentum/compositor acceptance, and do not change the limits above.

Cancellation stays owned by those native capture listeners; the timeline does not
need a second imperative cancellation API. The installed-driver controls cover
all four input events plus already-queued replays and disposal/remount.

## Corrections after a browser clamp

When rows above the viewport shrink, the automatic correction moves the offset
by the same amount. Stock Virtua applies it relatively unless the target reaches
the end, but the layout that `scrollBy` forces clamps an offset beyond the new
end first, so the shrink lands twice: once from the clamp, once from the
correction. WebKit reports an integer `scrollTop`, which reads up to 1px short
of a fractional end, so a reader at the bottom missed the end test there while
Chromium's fractional offset met it.

The element driver takes the absolute path when the target lies within 1px of
the end, rounding outward as before, and when the last observed offset lies
more than 1px beyond the new end, scrolling to the exact target. Interior
corrections, growth and prepend shifts stay relative. The installed-driver
regressions clamp the fake viewport like a browser and cover an integer offset
at a fractional end and a shrink larger than the reader's gap to the end.
`ChannelTimeline` treats an upward offset that arrives with a shrink as reader
input only after a gesture; while following, it re-pins the bottom instead of
demoting to Jump-to-latest.

## A shift outlives a late measurement frame

While older rows are being prepended (`shift`), the store compensates every
resize so the reader keeps their distance from the end, and it ends the shift
from its scroll-end timer, 150 ms after the shift jump's own scroll event. The
prepended rows are measured in the frame after that jump, together with the
former first row, which the same render re-laid out as a continuation without
its day divider and author header. When that frame runs late, the timer fires
first and the batch meets native policy, which keeps the viewport start: the
former first row sits at that start, so its shrink is dropped, and so is the
growth of a prepended row whose estimated bottom WebKit's integer `scrollTop`
reads short of. A reader at the top of history who loaded older messages saw
their content move about 76 px on Linux WebKit.

The store counts the rows a shift prepends and, at scroll-end, keeps shift
policy while any of them inside the rendered range is still unmeasured; the
resize batch that measures them ends the shift. A shift whose prepended rows
are not mounted ends at scroll-end as before, a batch inside the window is
unchanged, and a visible row that grows after the shift (an image loading)
keeps the viewport start as before. Installed-store regressions cover the late
batch, unrelated/partial batches before completion, the stock window and an
unmounted prepend.

## Viewport size is delivered in the observer callback

Row resizes are delivered in the next animation frame, outside the native
ResizeObserver callback. Rendering from that callback can mount rows at the
same DOM depth and cause WebKit's "loop completed with undelivered
notifications" cycle. The scroll viewport's own size is an exception: it is
delivered in the callback. It can only mount rows that are deeper in the DOM,
which the browser may observe in the same frame without that cycle. Their own
sizes are still deferred.

When the viewport size arrives, the driver also reads the native scroll offset
first. A channel switch scrolls imperatively before its scroll event is
dispatched; without that read, the first range is computed at the old offset
and the correct rows render one frame later.

Together these let the first rows of a warm channel switch paint one frame
earlier (median three frames to two). On one Mac, the
`channel-opening` warm-switch median went from 52–58 ms to 40–42 ms (24 samples
per run, interleaved runs). Installed-driver regressions cover immediate
viewport delivery with deferred rows, removal and remount, and the offset read
in LTR and RTL.

## Sizes known before measurement

An unmeasured row mounts hidden at the default size. Its measurement arrives a
frame later and costs a synchronous render and, when the row is above the
reading position, a correction that interrupts momentum on Mac WebKit. A size
cached before mount, like a `cache` snapshot entry, avoids all of that: the row
renders visible at its final offset, and an equal measurement is dropped before
any state change.

`Virtualizer` therefore accepts `estimateSize(index)`, returning a size or
`undefined`. The layout consults it at creation for entries the snapshot lacks;
snapshot measurements take precedence. Each length change carries the estimator
of the render that made it, since a latest-ref would still map the previous
render's indexes. Appended items are seeded without a jump. Under `shift`, the
jump is the sum of the prepended predictions plus the size change of the item
that was first, which lost its day divider and author header to its new
predecessor. The shift's wait above covers only unmeasured rows, and a predicted
prepend has none, so that item's late measurement would otherwise meet native
policy. The application cannot correct it after the commit: until the jump's
scroll event, the store's offset still precedes the jump. That item is therefore
consulted first, and if it is `undefined` no prepended item is seeded: they stay
unmeasured, so the wait covers the frame that measures them together with it.
A removal from the start predicts the new first item the same way. Otherwise
`undefined` keeps stock behaviour for that index, including the wait.

The handle's `resize(pairs)` sets new predictions after a width or font change
through the measured resize path, which VGrid's `resizeRows` already uses: rows
above the reading position are compensated and rows below are not. Like the
viewport path, it first reads the native offset: a jump or correction earlier in
the frame can precede its scroll event, and a stale offset would misclassify
rows near the viewport start. A prediction is not a measurement, so mounted
targets among the pairs are unobserved and observed again. The fresh observation
reports the real size, which confirms the value or corrects it; otherwise a
mounted row whose height did not change would keep a wrong prediction until it
remounts. Re-arming also drops the target's deferred entry: it predates the new
size, and flushing it in the next frame would revert the size before the fresh
observation arrives. The driver's element-to-index map becomes an iterable
`Map`; unmount still deletes entries. `resize` renders synchronously: call it
outside React render and effects, with committed indexes. The timeline calls it
at most twice per new Virtualizer, for unmeasured rows that are not mounted and
before any reader input
([docs/channels.md](../docs/channels.md#predicted-row-heights)); its post-commit
reconciliation (width, font or content changes) is deferred.

Predicted and measured sizes are deliberately indistinguishable, as restored
sizes already are. A prediction off by any fraction of a pixel costs the stock
correction.

Stock Virtua sizes unmeasured items at `itemSize`, or, without it, estimates
that default once: when measurements that change cached sizes exceed the
viewport, it becomes the median cached size, and `bufferSize` is ignored until
then, even for items appended later. Exact predictions never complete that
estimate, and a fixed `itemSize` cannot know the items an estimator leaves
unknown, which are by construction unlike the ones it seeds. On a channel whose
rows are mostly membership changes, the timeline's rough `itemSize` (80px)
missed every membership row (52px), which then mounted hidden and corrected:
171 corrections over a 640-row upward traversal against 138 with stock sizing
in Chromium, 172 against 139 in WebKit. A Virtualizer created with an estimator
therefore keeps the estimate, with `itemSize` (or 40) as its initial default and
the stock trigger, but samples only measurements of items that had no size: a
seeded item's equal measurement never reaches the sample, a snapshot's entries
are not in it, and the handle's `resize` is not a measurement. Its `bufferSize`
applies without waiting. One created without an estimator is unchanged. That
traversal then corrects 125–130 times in Chromium and 135–137 in WebKit.
Compensation policies, observer deferral, the scheduler and momentum handling
are unchanged; VList and WindowVirtualizer do not accept the prop.
`ChannelTimeline` passes `itemSize` and the estimator together, only to a
Virtualizer created with its model ready; one created earlier keeps stock sizing
for its lifetime ([docs/channels.md](../docs/channels.md#predicted-row-heights)).

Installed store/driver regressions cover seeding behind a snapshot (an equal
batch leaves the store version unchanged), a predicted prepend whose late equal
frame is a no-op, a prepend whose former first item is unknown (nothing is
seeded, and its late frame keeps the reading position), removal from the start,
an append, partial predictions under the shift's wait, resize policy over
predicted sizes, re-observation of mounted targets only, a resize that drops the
row's deferred measurement, a resize after a jump whose scroll event is still
queued, and a resize after a withheld prepend (the shift keeps waiting for its
late frame). A jsdom test mounts
the real `Virtualizer` for the prop and handle. Each fails on the previous
bundle, and copied-bundle mutants of each new hunk fail at least one of them.
The estimate's regression (the default becomes the median measurement of
unseeded items, not of every cached size, once they exceed the viewport) fails
on the previous bundle; three more hold on both and fail its mutants: stock
estimation still samples every cached size, a seeded Virtualizer's buffer does
not wait, and `resize` pairs do not complete the estimate.
They do not establish that browser measurements equal predictions (heights are
LayoutUnit-snapped and divided by zoom), or how either engine treats `observe()`
on a target it already observes; unobserving first avoids depending on it.

## Automated checks

```sh
bin/pnpm install --frozen-lockfile
bin/pnpm typecheck
bin/pnpm exec vitest run src/features/messages/virtua-compensation.test.mjs \
  src/features/messages/virtua-predicted-sizes.test.tsx \
  src/features/messages/ChannelTimeline.test.tsx
bin/pnpm test:browser history-loading.spec.mjs image-scroll.spec.mjs initial-position.spec.mjs row-heights.spec.mjs \
  --project chromium --project webkit --no-deps --workers=1
```

The driver/store/observer contracts evaluate the installed React ESM, not a
copied implementation. They cover active and inferred-idle corrections, zero
jumps, positive/negative measurements, absolute edges, horizontal RTL, overlapping
restoration, CSS priority, disposal/remount, later declarations, platform controls,
and unchanged imperative instant/smooth calls. Copied-bundle mutation controls
must fail when the production invocation, overlap/dispose restoration, priority,
or iPad exclusion is removed, or an inferred-scrolling gate is introduced.
These tests use a fake viewport; they cannot establish native painted pixels.

## Native acceptance and limits

Use an isolated system WKWebView, fixed data, no live identity, and phase-bearing
native wheel/momentum input confined to that window. Freeze/hash the source,
installed bundle and runner before each run. Start with a settled production
ChannelTimeline, prepend during momentum, then repeat with a pause longer than
150ms before the final momentum event. Compare stock, the superseded draft, and
the replacement. Capture source video frames separately from DOM/anchor traces.

Require both painted content and the correct identified reading anchor. Repeat
with a fresh reversed gesture, a second prepend at the bottom, a fresh upward
gesture, positive/negative row measurement changes, and explicitly gated local
images. Check restoration and continued movement, not just final scrollTop.
Exercise imperative reveal/restore/bottom controls separately. A pending image
placeholder and bottom rubberband/fractional edge gaps are not missing tiles.

Observed on macOS 26.6.2: stock and a paused old-draft trial sustain blank message
pixels; the replacement preserves content and correction anchors in the matched
native trials. Repeated native gestures and local images continue to paint, with
the braking tradeoff above. Ordinary Chromium/WebKit browser history, image and
initial-position journeys provide additional behavioral coverage, **not equivalent
native momentum/compositor evidence**.

The fixed-data native fixture does not fetch real older history. Three-second
movies are not four seconds of pixel evidence just because DOM traces run longer;
movie and JavaScript clocks are not synchronized. These bounded results are not
signed-package/cross-platform acceptance or verification of the original user's
sustained real-message incident. Keep the change draft until that acceptance is
completed; do not restart a running app without coordination.


## Base UI 1.8.0: native choice reset

`@base-ui__react@1.8.0.patch` adds native form-reset listeners to Checkbox.Root
and Radio.Root, with RadioGroup supplying its existing state reset, in their
shipped ESM and CommonJS modules. Without it, resetting
an uncontrolled choice restores the hidden native input but leaves Base UI's
visible checked state unchanged. The shared Buzz wrappers continue to delegate
choice state, keyboard handling and form participation to Base UI.

The listeners run in the next task, after native reset and ancestor cancellation;
a microtask can run before the browser completes its default reset action. Each actual
input owns its `form` binding, including external `form=` associations, disabled
radios and radios mounted after their group. Cleanup prevents queued work after
unmount. The group retains its existing uncontrolled state setter; repeated
radio notifications are idempotent. Controlled values remain with the caller,
and each hidden input restores its current checked state if the owner leaves
that value unchanged. Stable callbacks read the latest values when the owner
updates them during reset. No synthetic change event or ordinary change callback
is emitted. No other primitives are patched.

Remove the patch when a pinned Base UI release passes the reset regressions in
`src/shared/design-system/ui/controls.test.tsx` and the design viewer's native
reset browser check without it. A frozen install must reproduce the patch:

```sh
bin/pnpm install --frozen-lockfile
bin/pnpm exec vitest run src/shared/design-system/ui/controls.test.tsx
bin/pnpm design:test:browser
```

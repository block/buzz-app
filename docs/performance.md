# Local browser performance runs

Run one checkout with a few parameters:

```sh
source bin/activate-hermit
bin/pnpm test:browser:install # once per pinned browser version
bin/pnpm perf --scenario channel-open --repeat 5 --cpu 4 --out results.json
```

`--scenario all` is the default. A case name runs only that case; a group
(`channel-open`, `scroll-paging`, `thread` or `editor`) runs every case whose name it prefixes, so
`scroll-paging-fast` excludes its variants. `--cpu` sets Chromium's CPU slowdown factor
(1 means unthrottled); it does not throttle network or the fixture server.
`--repeat` defaults to 5. Every sample gets fresh browser storage, signed
histories and server state; a production frontend build is shared by the worker.
One worker runs serially with no retries. Required CI runs every case once in
**Browser measurements** without timing thresholds. Locally, use `pnpm perf`;
`pnpm test` / `just scan` do not run these cases.

The existing browser fixture owns the production React/services/IndexedDB/Virtua
app and modeled local HTTP broker. The runner owns settings and measurement
windows; scenarios own setup, actions and proof that the intended work occurred.
There is no comparison engine, second checkout or prescribed optimization target.

## Measurements

The operation runs from immediately before the action until the timeline has
visible rows and unchanged visible geometry for at least 200ms across at least
three samples. Each sample reports Chromium `Performance.getMetrics` deltas and
browser timings, in milliseconds:

| Metric | Meaning |
| --- | --- |
| `scriptMs` | `ScriptDuration`: JavaScript execution |
| `layoutMs` | `LayoutDuration`: layout work |
| `styleMs` | `RecalcStyleDuration`: style recalculation |
| `taskMs` | `TaskDuration`: main-thread task time |
| `durationMs` | Browser wall time through the settling barrier |
| `loafBlockingMs` | Sum of browser-reported long-animation-frame blocking, from frames overlapping the operation, including settling |
| `firstRowsMs` | Captured browser click event to visible target rows across two rendering updates |

The first-rows endpoint gives the browser a paint opportunity; it is not a
compositor screenshot or proof that every pixel finished painting. The settle
barrier observes row IDs/positions/heights and scroll geometry, not arbitrary
future async work. A ten-second deadline (30 seconds for thread actions and
60 seconds for paging through history)
fails the sample instead of reporting an unfinished operation as a win.
Counter windows also include measurement
overhead and protocol dispatch around the action. Measured actions use browser
input: JavaScript invoked directly through the automation protocol can be absent
from `ScriptDuration`, even when included in `TaskDuration`. Categories overlap: do not
sum them or interpret them as CPU percentages. No forced GC is performed.

`loafBlockingMs` uses Chromium's [Long Animation Frames API](https://developer.chrome.com/docs/web-platform/long-animation-frames).
Its `blockingDuration` accumulates blocking beyond the 50ms task budget, with
rendering included in the longest task. It is not simply frame duration minus
50ms, a frame count, or an FPS measure. The observer begins at measurement start;
unsupported browsers fail explicitly rather than reporting zero. Raw
`recording.longAnimationFrames` retains intersecting entries as `startMs`
(relative to recording start), `durationMs` and `blockingDurationMs`.

Every frame overlapping the operation contributes its entire blocking duration,
including a frame that starts before measurement or finishes after the endpoint.
This avoids reporting zero when a busy opening frame starts just before the
recording marker. It is frame attribution, not exact clipping: boundary frames
can include hover/setup work before the marker or work after the endpoint.
Frames entirely outside the operation do not contribute.
The API's aggregate cannot be split accurately. After counters stop, collection
allows two further rendering opportunities and a queued task for late LoAF
delivery. This bounded drain retains the final frame in our Chromium regression
probe, but is not a presentation acknowledgement: unusually delayed presentation
feedback can still omit a trailing entry. The drain is outside the existing
duration and counter windows. Recorder overhead remains included; no subtraction
is applied.

`channel-open` measures two independent cases with fresh state:

- `channel-open-cold` clicks a never-opened, never-hovered channel and requires a
  head read during opening.
- `channel-open-hover` gives the same unopened channel a 150ms hover head start,
  then clicks whether preparation is finished or still running. CPU throttling
  applies during hover too. There is no response-completion or idle wait.
- `channel-open-cold-markdown` repeats the cold case with the
  [Markdown corpus](#corpus-variants).

Every case measures click-to-first-rows and browser work during opening plus
settling. Work completed before the click earns the hover case a head start;
remaining preparation can contribute to the measured work. Browser-counter
windows exclude pre-measurement hover work; LoAF totals include whole overlapping
boundary frames as described above. `work.hoverMs` records the requested lead and raw
`recording.hoverLeadMs` records the actual browser hover-to-click interval, which
can exceed 150ms due to browser scheduling and protocol dispatch. Head-read counts
before and during opening are diagnostic evidence; hover does not require zero
new reads. Each target has 120 mixed-height text messages; the existing app chooses
how many it initially loads. The corpus content and timestamps are fixed; signing
identities are ephemeral.

The hover case replaces `channel-open-prepared`, which waited for a completed head
response and an idle opportunity. Those older results are a different workload;
collect a new baseline rather than comparing them as equivalent.

## Scrolling

```sh
bin/pnpm perf --scenario scroll-short --repeat 5 --cpu 4
bin/pnpm perf --scenario scroll-long --repeat 5 --cpu 4
bin/pnpm perf --scenario scroll-paging --repeat 5 --cpu 4
```

All scroll scenarios use the same observer, counters, fresh contexts and result format:

| Scenario | Workload |
| --- | --- |
| `scroll-short` | 800px upward at 1600px/s within the loaded head of a 120-message channel |
| `scroll-long` | 12,000px upward at 4000px/s across a 360-message channel, fully loaded before measuring |
| `scroll-paging-fast` | Repeated 2500px upward gestures at 25,000px/s through 640 mixed-height messages, with 100ms added older-response delay, until the oldest message is visible |
| `scroll-paging-delayed` | The same complete traversal with 500ms added older-response delay |
| `scroll-paging-fast-keyboard` | `scroll-paging-fast` in keyboard modality |
| `scroll-paging-fast-markdown` | `scroll-paging-fast` through the [Markdown corpus](#corpus-variants) |
| `scroll-paging-fast-first-seen` | `scroll-paging-fast` with [first-seen](#corpus-variants) older pages |

The long case loads older pages without traversing them first, so the gesture
encounters rows the virtualizer has not yet mounted/measured. Setup waits for
page processing to finish, rejects the history-limit notice, then settles geometry.
Neither short nor long windows permit older-page reads. They isolate rendering
from pagination.

Wheel input lands in the timeline gutter, away from message hover. Setup reaches
Messages through palette arrow keys, which set `html[data-keyboard-navigation]`;
in that state the app prepares each newly mounted row's full action bar. Every scroll
case except `scroll-paging-fast-keyboard` therefore ends setup with a real
pointer press at the gutter point. The press clears keyboard modality and
focuses the message list, as clicking into a conversation does, so the reading
observer runs during the gesture. `scroll-paging-fast-keyboard` only moves the
pointer there, keeping keyboard modality and focus outside the list as after
palette navigation. Each sample asserts its modality and focus before measuring
and records `work.modality`. Scroll results recorded before the pointer press
ran in keyboard modality, like `scroll-paging-fast-keyboard`; rerun baselines
before comparing them.

The short and long Chromium gestures must produce wheel events, scroll-offset movement
of at least 80% of the request, multiple visible messages and changed visible IDs.
Raw frames and work receipts record the requested distance/speed, history size,
released pages, wheel count and observed rows. `scrollTopRangePx` is the observed
offset range, including virtualizer corrections; it is not physical input distance.

`--scenario scroll-paging` runs every paging case; so does the default `all`.
Use a full case name to isolate one. Each case has its own samples and
summary; the runner never pools their metrics. The same `--cpu` setting applies
to all. There is no delay parameter or implicit CPU matrix.

Paging cases start with only the head loaded. The modeled HTTP broker adds the named
delay to each older-page response; there are no page-completion or idle waits
between gestures. Arrivals compete with scrolling and pending virtualizer
corrections, the workload behind [the held-range prepend fix](https://github.com/block/buzz-app/pull/1066).
The existing installed-Virtua tests protect that correction's correctness; these
scenarios measure its browser cost. They use normal-height text, unlike the
taller short/long corpus. Fast retains pressure from closely spaced arrivals;
delayed exercises more waiting while the user keeps scrolling. These are
repeatable modeled conditions, not production latency percentiles or a guarantee
that every run hits a particular scheduling race. The delay starts after the
fixture computes its response; browser queueing, transport and verification add
to it. `work.olderReleaseDelaysMs` records actual server-side release delays.

Paging measures a complete traversal, not however many pages fit a fixed time:
input continues until the oldest message is visibly in the viewport, with a
200-gesture safety bound and a 60-second recording deadline. Those bounds allow
for the intentional per-page waits in the delayed variant. Successful samples
require real wheels, multiple older reads, all expected older fixture IDs in
released responses, and the oldest message still visible after settling. Work receipts record gesture/page counts, unique older rows
received and the endpoint ID. A stalled traversal fails; it cannot win by doing
less work. There is no mount-count target or automatic performance verdict.

These variants replace the experimental zero-delay `scroll-paging` workload;
collect new baselines rather than treating those old results as equivalent.

`rafMaxGapMs`, `rafP95GapMs` and `rafGapsOver50` describe animation-frame callback
cadence during the gesture. Raw `gestureStartMs` and `gestureEndMs` timestamps
are relative to the recording start: the first observed wheel event and the
browser marker after Chromium reports the synthetic gesture complete. For paging,
that marker follows the last gesture and its visible-oldest check; gaps between
successive gestures remain inside the cadence window. The end includes the
marker's protocol dispatch. Gaps are clipped to those boundaries,
including partial gaps before the first and after the last callback inside the
window. All callbacks count, including stalls when the scroll offset is unchanged.
The settling tail after the end marker is excluded from cadence only:
`scriptMs`, `layoutMs`, `styleMs`, `taskMs`, `durationMs` and `loafBlockingMs` cover scrolling
plus settling, with the same measurement overhead.

Recordings without these gesture timestamps used whole-operation cadence,
including the settling tail. Their cadence values are not comparable with the
new definition; rerun baselines before comparing. That cadence change added no
summary metrics.
Callback gaps expose main-thread stalls, not compositor FPS or a measured
dropped-frame count. No generic blank-time, overlap or visual-shift verdict is
inferred from them.

## Corpus variants

The default corpus is inert prose: an identifying line plus repeated sentences,
authored by the viewer. Two opt-in fixture options change one property each, so a
variant differs from its base case only there.

`markdownMessages` (the `-markdown` cases) ends seven rows in eight with common
chat content after the same height-varying text: colon prose, a second
paragraph, a bare URL and a Markdown link, an `@mention` bound to a fixture
profile, a nested bullet list with inline code and emphasis, a fenced code block,
or a quote with emphasis and strikethrough. The eighth row stays inert prose.
Lists are bullets only, because browser helpers find the timeline through its
single ordered list.

The app verifies each relay event's signature once per connection and reuses that
proof. Its startup unread read takes the newest 500 events across joined channels,
so default history reaches the app before measurement, including 480 of the
620 older paging rows. `firstSeenHistory` (`scroll-paging-fast-first-seen`) adds a
joined `busy` channel whose 500 newer messages fill that read, as busier channels
do. Older pages then first reach the app, and are verified, during the measured
traversal. The fixture records the event IDs of each modeled HTTP query response
when it computes the response, which for a held older page is before release.
Paging samples record `work.olderRowsServedBefore`, and the first-seen case
requires zero. This proves which events arrive first-seen, not when background
verification of the startup read finishes; setup does not wait for it. The option
adds 500 fixture signatures to setup and one sidebar row. There is no first-seen
channel-open case: verifying its one 20-event head page is within that case's
sample-to-sample variation, and the busy channel also changes unread state
before the click.

## Rich thread lifecycle

`--scenario thread` measures `thread-open-rich`, `thread-close-rich` and
`thread-reopen-rich` independently with the existing metrics. Each sample starts
fresh; close and reopen establish their prerequisite open state outside the
measurement. Normal pointer-triggered panel animations remain enabled.

The signed corpus has 120 replies from twelve participants, including eight
agents, and eight additional channel threads.
The auxiliary roots fit in the initial channel page before the measured thread
and use reply summaries
without inserting their replies into the top-level history. Initial setup requires
all eight auxiliary roots and their rendered reply counts. Each phase records
the actual mounted channel row IDs and checks
that all eight roots remain mounted at the start of its measured action.
Channel roots use distinct millisecond ordering from ordinary rows, so fresh
signing identities cannot change their order or bubble grouping.
Twenty nested replies remain collapsed as in an ordinary opening; the visible tree mounts 100 direct replies
plus its root. The mix includes prose, mentions, links, Markdown tables, task
lists, code, quotes, fifteen image previews and ten video previews. Media uses
the repository's local image/video assets, not network downloads. Visible images
must decode, videos must have loaded data and dimensions, and both transitions
and thread geometry must settle. Offscreen lazy images retain normal loading.

Each measured action also observes the channel through the existing 200ms
geometry barrier. Close first waits for actual thread DOM removal and the
channel's original width, then for Virtua's pointer hold to end, settled channel
geometry and restoration of its reading anchor. Draft setup settles before
measurement. Close also records channel geometry before/at/after the window and
fails if another settling check reveals reflow after the endpoint. Every phase
checks the channel draft, and reopen checks the saved thread draft. These are
work-completion checks, not new timing counters. The workload covers populated
thread mounting and panel reflow, not video playback, gallery interaction,
expanding nested replies or live agent streaming.

## Results and iteration

JSON contains raw per-frame geometry, work evidence, all samples and per-metric
median/min/max/sample count. Only wholly passing samples enter summaries. Inspect
the top-level status and each run's errors before using a number; a failed command
is never a successful optimization. Runtime/source identity, dirty status, CPU
setting, viewport, host load and setup timing accompany the samples. A dirty
listing is not a content hash: tie claims to a clean commit.

Every invocation creates a fresh ignored `test-results/perf/run-*` evidence
directory. Existing fixture evidence and failure screenshots are retained there;
the summary defaults to that directory or writes the exact `--out` path. Reusing
an explicit output path replaces that summary. Traces/video are off to reduce
measurement overhead; use the existing functional browser runner for diagnostics.

Choose any relevant metric (including scripting) as the objective, keep the
scenario and settings fixed, and inspect all other metrics plus actual work.
Keep baseline JSON, make one change, rerun, and confirm promising changes with
repeated samples and the existing correctness tests. Use an idle machine and
alternate baseline/candidate runs when making a performance claim. Comparing
different CPU settings, browsers, fixtures or concurrent host loads is not a
controlled comparison. The runner does not decide which tradeoffs are acceptable.

The channel, scrolling and thread cases use Chromium with modeled backend responses (immediate except
for the named paging delays),
HTTP interception (which disables HTTP cache) and preloaded fonts. Channel and
scrolling workloads use text; the rich thread workload adds local media and
multiple authors.
These cases do not measure production network latency, native hosting, WebKit,
long-session memory growth or application startup. Add those as explicit workloads
when needed rather than changing the meaning of existing samples.

## Editor responsiveness

The `editor` group measures the production editor while input continues
on an external schedule. It reports current performance and workflow outcomes;
there is **no frame-budget or acceptance-success gate** yet. `passed` means the
measurement ran with its workload, not that the editor met a responsiveness goal.
Read `outcomes` alongside timing summaries. No production code is instrumented.
CI runs these cases once in Chromium with the other perf scenarios; it does not
gate on editor latency or workflow correctness.

```sh
bin/pnpm perf --scenario editor --repeat 5 --cpu 4 --interval 40
bin/pnpm perf --scenario editor-busy-unique --repeat 5 --cpu 4 --interval 20
bin/pnpm perf --scenario editor --repeat 5 --browser webkit --cpu 1
bin/pnpm perf --scenario editor-probe --repeat 1 --cpu 1
bin/pnpm perf --scenario editor-probe --repeat 1 --browser webkit --cpu 1
```

`--interval` is milliseconds between scheduled keys, including Enter/Tab and
navigation. It is a workload parameter, not an artificial wait for UI success.
Try 20, 40 and 80ms when exploring how completion behaves as typing accelerates.
WebKit supports only editor cases and `--cpu 1`; its engine has no equivalent of
Chromium's CPU slowdown control. Its busy scene supplies application load.

| Flow (each in sparse and busy scenes) | Measured interaction |
| --- | --- |
| `editing` | Ordinary typing, five backspaces, four caret movements, three Shift+Left selection extensions, deletion and continued typing |
| `open` | Ordinary typing then `@`, observing the six available local choices without immediately filtering them away |
| `unique` | Type `@Quill`, immediately Enter, continue typing; require the exact QuillUnique recipient in the final draft |
| `choose` | Type `@A`, move down twice among four matches, Tab to select Axel, continue typing |
| `directory` | Type `@Directory P`, observe the outside-channel Directory Person result, including the production 200ms debounce and modeled search |

The sparse scene has three messages, five named channel members plus the viewer,
and a separate directory-only person. The busy scene retains three populated
thread views with 48 replies each alongside a 120-message Markdown channel. It
uses real formatted text, code, links, images, and 18 looping, muted video
attachments. It types in the active thread while signed incoming replies arrive
about every 150ms through the production broker. Runtime receipts record mounted
rows, thread/media counts, emitted reply IDs and their DOM/rendering opportunities.
The workload fails if background messages never reach that boundary. This is a
bounded stress model, not a reproduction of hundreds of animated avatar players
or proof of a leak. It does not replay hours of session history.

The editor fixture honors single byte ranges for its unchanged local media.
Bounded, open-ended and suffix ranges return sliced 206 responses; unsatisfiable
ranges return 416. Malformed, multiple or unsupported ranges retain whole-file
200 delivery. Non-range delivery is unchanged. Linux WebKit also launches with
`WEBKIT_GST_ALLOW_PLAYBACK_OF_INVISIBLE_VIDEOS=1`: its GStreamer backend otherwise
suspends muted offscreen players, contrary to this workload's eighteen playing
videos. JSON records that environment setting. Busy setup and completion require
all eighteen videos playing; setup also requires all three thread views.
Linux WebKit also initializes looping with one observed seek while paused before
the once-only play calls. Its native segment-loop initialization otherwise can
repeat the opening frame despite loaded/unpaused receipts. This setup uses the
same asset, keeps looping enabled, and performs no reload or play retry. The
native regression requires three complete decoded-frame traversals, rather than
accepting the first replay as proof of sustained looping.
The completion check follows recording and uses the existing assertion deadline
to observe that exact state after normal loop seeks. It retains the immediate
snapshot too; it does not extend observer windows or revise stored outcomes.
These repairs prevent rejected range responses and suspended players from
silently reducing the media workload. They are versioned harness changes, not a
product speedup: apply the same repair to both
comparison sources and record the harness commit. Keep earlier results under
their original harness version; do not pool results across these versions.

The test process schedules key-down/up commands without awaiting prior commands
or asserting each intermediate UI state. All acknowledgements are collected
after dispatch. Raw planned/sent/acknowledged timestamps expose driver drift;
browser event timestamps and capture-handler times expose input queueing.
Every sample keeps the full draft, selection, menu and recipient observations.
Slow Tab acceptance can lose focus, and Enter can send a partial draft: these are
recorded outcomes against the disposable relay, not discarded timing samples.

| Metric | Endpoint and limitation |
| --- | --- |
| `inputQueue*Ms` | Trusted key event timestamp to capture handler; includes waiting before editor processing |
| `<phase>NextFrame*Ms` | Key event to first subsequent animation-frame callback; it need not contain the correct response |
| `<phase>State*Ms` | Key event to a frame where the expected text/selection, choices, highlight or accepted recipient is observed |
| `suggestionsState*Ms` | Final prefix to the expected options; kept separate from intermediate text-only `filterState` measurements |
| `activeRafGap*Ms` | Callback gaps from the first key through the first frame following the final key's handler, including final-key blocking |
| `dispatchLateness*Ms` / `dispatchAck*Ms` | External scheduling drift / command acknowledgement latency; not editor rendering latency |
| `probe*Ms` | Time spent sampling editor/menu DOM in each frame; included in timings, never subtracted |

All distributions include p50/p95/max within each sample. These are DOM states
observed before rendering, **not compositor presentation latency or FPS**. Native
selection is observed through the real editor's public selection projection.
Event Timing entries, where supported, are supplementary rounded observations;
unsupported engines record the capability explicitly. Instrumentation adds work.

Intermediate states can be coalesced when several inputs arrive between frames.
`UnobservedStates` and `ObservedBeforeNextInput` accompany timings, and raw missing
observations remain null. Never interpret the conditional latency of observed
states without those counts or claim that an unobserved acceptance was fast.
Missing, reordered or untrusted input retains raw evidence but contributes no
per-phase timings: a later key must not inherit a missing key's action label.
Text, selection and highlight states must be observed before the next key's
handler runs; a later backspace cannot retroactively satisfy an earlier typing
observation. Query-result and accepted-recipient observations can persist across
later input.
Acceptance timing follows the recipient and closed menu even if subsequent typing
has already extended the draft. Final text, selection, identity, focus, and any
accidental publication remain separate correctness checks in `outcomes`.

Collection ends after the expected final state exists across two frame callbacks,
or five seconds after input acknowledgements finish. The latter is labeled
`deadline`, not a zero-duration success. Quiet DOM alone cannot end a pending
directory search. The deadline is an observation bound, not a speed threshold.
The `editor-probe` calibration injects known main-thread work and delayed results
to verify input queueing, the final-key frame window, external dispatch and late
response observation. Its assertions validate the recorder, not product speed.

Compare repeated runs on the same engine, source, hardware, input cadence and
scene; alternate CPU settings when evaluating resource sensitivity. The JSON
retains individual outcomes, per-key observations and raw frames for hill climbing.
Playwright WebKit on macOS is useful engine evidence, but it is not the packaged
Tauri app, native IPC or a hardware presentation measurement. Keep native and
physical-device acceptance separate.

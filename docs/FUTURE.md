# What is left

Written 2026-09-13, against AutoLL-3 at 0.5.0. Revised 2026-09-14 when the day's
action allowance was removed (§7) and the 2026-09-12 review's correctness list
was cleared (§1), and again on 2026-09-15, when every decision in §4 was
answered and a Time Search was given precedence over the engine — decided and
built the same day, so it is not listed below. Revised again on 2026-09-23, when
the ordering moved to `ROADMAP.md`'s calendar and five items were added
(§2.8–§2.11 and §3.13), and a sixth the same day (§2.12). §1 and §6 gained what
making 1.8.4 turned up, on 2026-10-03. Later that day 1.9.0 closed §1's last
item, and §4.5 reopened a question §7 had closed on Genie+'s two-hour rule.

This is the standing list of what is not done: the items still open from
`PLAN.md` and `UX-PLAN.md`, the
defects the 2026-09-12 review confirmed and the fixes of that day did not
cover, the decisions waiting on an answer, the questions only a park day can
settle, and — at the end, deliberately — the things already decided against, so
they are not proposed again as fresh ideas.

The two plans keep their reasoning. This file keeps the work.

**How to read it.** Each item says where it lives in the code, how big it is,
and what could go wrong doing it. Sizes are honest rather than encouraging:
_small_ is an evening, _medium_ is a session or two with tests, _large_ is a
week and a decision. Nothing here is scheduled; the ordering at the end is a
recommendation, not a plan.

**The main trip is the goal, and the week up to its booking morning is a
freeze.** That is the constraint every judgement below is made against. The tool is
usable today; everything here makes it better, and nothing here is required.

---

## The short list

If only four things get done before the main trip, these — in `ROADMAP.md`'s order,
which is now the one to follow:

1. **Back up the plan and what the learner has seen** (§3.13, ROADMAP item 12) —
   built: export in 1.3.0, restore in 1.4.0. Everything lives in one browser
   store on the phone, iOS deletes that store after about a week without a visit,
   and until then nothing got any of it off the phone.
2. **Warn before a held pass lapses** (§3.1's warning half, ROADMAP item 3) — the
   largest recoverable loss the tool still does not catch, and now an alert that
   reaches a pocket.
3. **Plan from the sofa** (§3.2, ROADMAP item 6) — but only if the reading taken
   twenty-one days before the rehearsal shows the date picker cannot serve the
   main trip.
4. **The overlay IDs** (§3.3, ROADMAP item 7) — a watch list built against the
   wrong Jingle Cruise ID matches nothing during the holidays, silently.

The timeline's names and tap targets (§2.1, §2.2), third on the previous list,
have moved to after the main trip: the day view is a planning aid, and a park morning
is better served by §2.8 and §2.9.

The correctness list above them is empty: §1 was cleared on 2026-09-14, and
with it the four screen defects that used to sit in §2.

---

## 1. Correctness still outstanding

**Nothing, as of 2026-09-14.** Every finding this section carried has been
fixed. Recorded here rather than deleted, because the section numbers below are
referenced from `UX-PLAN.md` and from the ordering at the end of this file.

What went, in the order they were listed: a Time Search committing outside the
shared action ledger, so it and the top-level Autopilot could modify the same
held pass; Home's on-visible refresh dying at the first tab switch, because
`useScreenState` compared React elements by identity while `withTabs` replaced
the active element on every change; a refusal burst flooding the saved activity
log, because the merge key carried the collapsed row's most-recent time and so
read every rewrite as a new event; a timed-out booking rendered as
"Request failed (0)" against this project's own rule that a status-0 result is
an unknown outcome; and the mount-time drop summary omitting the watched-days
record, so the Activity screen said "(not watched yet)" about drops it had been
watching for days.

Each landed with a test, and each of those tests was checked against a reverted
fix to prove it fails without it.

**The two small ones found while making 1.8.4 are fixed in 1.8.5:** Change and
Modify after removing guests act for the guests still on the pass, and a DAS
selection has its own protection key, read against DAS selections.

**The one left from Codex's review of 1.8.4 is fixed in 1.9.0: Autopilot's own
lost bookings are in the shared protection,** with their guests as the evidence
Plans settle them by. Before, Autopilot's action ledger alone held them: it kept
Autopilot from booking the attraction again, but a booking, change or cancel by
hand did not read it, and nobody could clear it. The ledger still holds them,
and clearing the protection gives that back. This section used to say nothing
was lost meanwhile because Disney refuses a second booking of an attraction for
the same guests. That was too strong: a refusal does not cover a booking Disney
applies late, after the attraction was booked again and that booking given up.
Clearing any protection still carries that risk; it is a judgment, not proof.
Codex's review of 1.9.0 found that a clear could give back a later request's
hold, and that Autopilot heard of a clear only through Activity's best-effort
record; 1.9.1 fixes both, and places a pass after midnight on its park day.


## 2. The screens

From `UX-PLAN.md` §9 and the gaps its phase notes record.

### 2.1 The timeline truncates every target name

**Done in 1.8.0** (ROADMAP item 32): windowless targets are named under Any
time instead of drawn, each side's width follows its columns, and tall bars
wrap. A short bar still keeps one truncated line. The finding as made:

At 360 px the Targets column is split again for every simultaneous bar, so
three full-day targets get about 50 px each and every name is cut. What shipped
instead of a fix was a `title` tooltip, which a touchscreen never shows. A
picture of the day that cannot say which ride a bar is for is a picture of
nothing.

_Where:_ `src/components/ll/DayTimeline.tsx:89,120-166`. _Size:_ medium. _Risk:_
wrapping, a legend and fewer columns each change the geometry the clash colours
depend on — settle it in the harness at 360 px first.

### 2.2 Timeline bars are 14–20 px tall and are the tap target

**Done in 1.8.0** (ROADMAP item 32): a 44 px invisible hit area on short bars.
The finding as made:

A bar's height is its time extent floored at 3 percent of the rail. Tapping one
is now how you reach a card or a booking. Phase 2 proposed an enlarged
invisible hit area so the drawn geometry stays honest; it was never added.

_Where:_ `src/components/ll/DayTimeline.tsx:18,24,46`. _Size:_ small. _Risk:_
adjacent bars' hit areas overlapping.

### 2.3 A second removal inside the undo window destroys the first undo

**Done in 1.8.1** (ROADMAP item 33): the strip keeps an Undo for every removal
made while it shows. The finding as made:

The undo holds one removal in a single state slot. Tidying two rows in a row —
the ordinary way to hit it — loses the first target's window, rank and flags
with no way back.

_Where:_ `src/components/ll/screens/Configure.tsx:91-101,296-317`. _Size:_
small. _Risk:_ keep the flash to one row at a time, or the footer grows
unpredictably at 360 px.

### 2.4 A Plan Check settings item opens Configure and abandons you

**Not a defect as written**, found while fixing it in 1.8.1 (ROADMAP item 33).
Every visit to Configure starts at its top, and the three safeguards are the
first thing there, so a settings item already lands on them. AutoLL-5's fix,
a scroll to the safeguards, moves nothing, and was not copied. What the item
does not do is mark which of the three chips it means; its text names the
setting in the chip's own words. The same look found the real gap next to it:
an item about an attraction opened its card wherever it was, often below the
fold. That card is now brought into view. The finding as made:

`Configure` accepts a focus of `{kind:'target'}` or `{kind:'setting'}` and
reads only the target case, so following a settings blocker drops you at the
top of a long screen with no indication of what to change.

_Where:_ `src/components/ll/screens/Configure.tsx:65-67`. _Size:_ small. _Risk:_
the screen is `fixed inset-0` with its own scroll pane, so scroll to a ref
rather than a hash.

### 2.5 The pre-trip checklist is missing three steps and has no way back into a finished one

**Done in 1.6.0 and 1.7.2** (ROADMAP items 27 and 31). "Windows set where
wanted" is a step you confirm, a finished step keeps its button, and
unrecognised attraction IDs have a row of their own. "Park and date chosen" is
not to be built (ROADMAP item 5). What follows is the finding as it was made.

It ships five of its eight steps: party, targets, an action armed,
notifications, Plan Check. "Park and date chosen", "windows set where wanted"
and "unrecognised attraction IDs" are absent — the last exists on Today as a
standalone red paragraph with no route to fix it. And the action button renders
only for steps that are *not* done, so a finished step cannot be reviewed.

_Where:_ `src/autopilot/checklist.ts:30-68`,
`src/components/ll/screens/Today.tsx:219-235`. _Size:_ small. _Risk:_ "windows
set where wanted" has no objective done state — make it an acknowledgement, not
a test, or it will never go green.

### 2.6 The timeline recomputes the whole day on every tick

`dayTimeline()` runs in the render body, and in burst cadence the status
updates every 1.2 seconds while `NavProvider` keeps the screen mounted
underneath whatever is pushed on top. `UX-PLAN.md` asked for a `useMemo` in
Phase 0 and still records it as unadded.

_Where:_ `src/components/ll/DayTimeline.tsx:76`. _Size:_ small. _Risk:_ the
dependency list must include the held plans, or the timeline freezes after a
booking.

### 2.7 The timeline's tooltips are in 24-hour time

**Done in 1.8.0** (ROADMAP item 32). The finding as made:

Every bar's `title` is built by interpolating a `ParkTime`, whose `toString()`
is zero-padded `HH:MM:SS` — so the string a screen reader takes as the bar's
description, and the only place a truncated name survives at all, reads
"20:15:00" where the bar itself shows "8:15 PM" through `<Time>`.

_Where:_ `src/components/ll/DayTimeline.tsx:123,163`, `src/datetime.ts:91-95`.
_Size:_ small. Fold it into §2.1, which is already rewriting how a bar carries
its name.

### 2.8 The park morning has no preflight — ROADMAP item 13

The pre-trip checklist disappears the moment the booking date is today — the
morning it would help most — and a park morning's go/no-go checks sit in four
places: the night-before list in the guide, the dry-run banner, the Test sound row
and the session-expiry line.

_Size:_ small. _Risk:_ a row that claims a readiness it never verified, which is
§2.5's lesson and ROADMAP item 5's.

### 2.9 Today does not point at the park the plan is for — ROADMAP item 14

The park is saved with `kvdb.setDaily` (`src/providers/ParkProvider.tsx:30`), so it
resets overnight, and only Configure mentions targets saved at another park. On a
morning whose plan is at EPCOT, Today reads "Nothing watched at Magic Kingdom on
this date."

_Size:_ small. _Risk:_ switching the park without saying so, which is a silent
change of its own.

### 2.10 The booking morning has no screen of its own — ROADMAP item 15

The highest-stakes moment of the year is nine or more sequential searches with the
date picker changed between them, on a different screen, and the failure that
cannot be undone is a pass for the wrong day.

_Size:_ medium, and specified by the rehearsal's booking morning rather than
before it.

### 2.11 Nothing captures an observation in the moment — ROADMAP item 16

_Size:_ small, optional. A note stamped with park time and the current park and
date, kept beside the activity log and carried in §3.13's backup.

### 2.12 A new build waits for a reload — ROADMAP item 17

After a deploy the phone keeps running the old bundle for up to ten minutes —
Pages' `max-age=600` on a fixed `bg1.js` URL — and an app already open never
checks at all. The owner wants it to reload on its own when it finds a new
version: in place, because a page reload drops an app the bookmarklet loaded,
and never while anything is running.

_Size:_ medium. _Where:_ a small module beside `src/autopilot/running.ts`, and
the loader's own steps. _Risk:_ reloading mid-run; stale chunks, which
content-hashed chunk names fix.

---

## 3. Booking intelligence

Outstanding items from `PLAN.md`, in the order they are worth doing.

### 3.1 Nothing rescues a Lightning Lane about to expire unredeemed — P3.3

Letting a pass lapse counts against you exactly as riding it does. When a held
pass's window plus grace is about to run out with no realistic chance of
getting there, modifying it onto a low-demand, always-available attraction
keeps the good one rebookable. It reuses `automodify.ts` wholesale; only the
trigger and the target differ.

_Where:_ `src/autopilot/automodify.ts:160-300`. _Size:_ medium. _Risk:_ it
spends an action on a pass you might still redeem, so the trigger has to be
late and conservative, and it must respect the same locks and budget as any
other move.

### 3.2 A target can only be added from a loaded tip board — P4.1's planning half

The booking-correctness half landed: targets carry park, date and your rank,
and the rank drives both the ordering and the Tier 1 hold. What did not land is
building the add list from the shipped data table, so on a plane or in a hotel,
with no tip board loaded, you cannot add a single attraction to a future trip day.

_Where:_ `src/components/ll/screens/Configure.tsx:87,275-300`. _Size:_ medium.
_Risk:_ the static table includes attractions Disney's tip board never returns;
a target added from it that can never match needs the "Not on today's list"
treatment rather than silence.

### 3.3 The holiday overlay IDs are unverified, and there is no alias — P4.7, §10.4

Jingle Cruise and Jungle Cruise are two IDs for one ride; so are Glimmering
Greenhouses and Living with the Land. Jingle Cruise runs the whole holiday season
and Glimmering Greenhouses from late November. A watch list built before the
overlays start, against the wrong ID, matches nothing once they run — and the durable half of this
(the "Not on today's list" group) will tell you, but only after the fact.

_Where:_ `src/api/data/wdw.ts:295-302,707-712`. _Size:_ small. _Risk:_ the
re-verification needs a live tip board once the overlays are running, which is
inside the freeze — so treat it as a data check with a one-line data edit, not a
code change.

### 3.4 The next drop is a time, not a countdown — P4.5

Today shows "Next drop: 1:17 PM". The plan asked for a counting header and an
audible cue at T−60s. The chime already exists and the audio context is already
unlocked for alerts; it is wired to alerts only. The tool's whole advantage is
being the thing that looks in the first two seconds, and that only pays if the
phone is out and foregrounded when the drop lands.

_Where:_ `src/components/ll/screens/Today.tsx:300-316`,
`src/autopilot/alert.ts:71-140`. _Size:_ small. _Risk:_ a ticking countdown is
another re-render per second on the screen most likely to be open during a
burst — keep it in its own component.

### 3.5 Pop-up drops and earlier-time drops are one list — P2.7

`dropTimes` is a flat array. Public tracking separates "a sold-out pass coming
back" from "one that jumps an hour earlier"; they run on different schedules,
and some attractions only ever show the second kind. Once you hold a pass, an
earlier return time is the only thing that improves your day — and the burst
that would catch it is currently spent on the wrong schedule.

_Where:_ `src/api/data/wdw.ts`, `src/autopilot/learned.ts:53-101`. _Size:_
medium. _Risk:_ it changes the shape of a table upstream merges also write, so
an untagged entry must keep behaving exactly as it does today.

### 3.6 Drop learning needs two distinct park days — P2.9

`LEARNED_MIN_DAYS = 2` means a four-to-six day trip spends the first half
gathering and the second half barely acting. Accepting a second observation
from the same day at a different hour, when the minute-of-hour matches, follows
the actual recurrence pattern.

_Where:_ `src/autopilot/learned.ts:15,53-101`. _Size:_ small. _Risk:_ loosening
the evidence bar is how noise becomes a schedule. Drop detection already fires
on cancellation flicker, and this must never reach the Tier 1 hold — see §6.

### 3.7 Autoswap assumes any Tier 2 is cheap to give up — P3.6

The victim choice prefers a non-Tier-1 and then sorts by rank, with no notion
of how reclaimable an attraction actually is: some Tier 2s stay selectable for
ten hours, others are gone by 9am. A swap that trades away the one you could
not get back is a worse day than not swapping.

_Where:_ `src/autopilot/autoswap.ts:100-130`. _Size:_ small. _Risk:_ the honest
data source is this build's own observations, not a paid table — with one trip's
worth the numbers are thin, so the fallback must be today's behaviour.

### 3.8 "Which guests" is one global switch — P4.8

A height restriction or a nap makes one attraction a subset ride and the rest
whole-party, and the only way to say so today is to flip a global safeguard and
accept it everywhere.

_Where:_ `src/autopilot/watchlist.ts:20-60`. _Size:_ medium. _Risk:_ guest IDs
in the watch list are persisted personal data on Disney's own origin, and the
activity log was already trimmed once for leaking guest records. Store IDs,
never names.

### 3.9 Nothing answers "which three do I grab first" at 7:00am — P4.3

Booking earlier in your window buys dramatically earlier return times, and
`PLAN.md` calls the 7:00am moment the most important minute of the trip. It is
the one moment the tool gives no guidance for.

_Where:_ `src/components/ll/BookingDate.tsx`. _Size:_ medium. _Risk:_ the
prohibition on scraping paid tables stands, so the honest version stays thin
until the build has observations of its own. `PLAN.md` §12 names this the first
thing to cut.

### 3.10 Crowd-level qualifiers are not carried — P2.6

All five Animal Kingdom drop times carry a crowd-level qualifier in the source
they came from, and the data table carries none. For a peak-season trip this
changes nothing — Animal Kingdom will be crowd level 7 to 10 and all five fire. It
matters on an off-season day, when the poller bursts at five dead times.

_Where:_ `src/api/data/wdw.ts:1091-1120`. _Size:_ small. The clearest candidate
to leave until after the trip.

### 3.11 Live standby waits are not in the ranking — PLAN §8

Ties break on the static average wait from the shipped table. On a crowd-level
10 day the gap between a 40-minute average and a 110-minute actual is the whole
decision about which of two tied attractions to chase.

_Where:_ `src/autopilot/priority.ts:31-36`, `src/api/livedata.ts`. _Size:_
medium. _Risk:_ a new external dependency on the booking path's ordering.
`PLAN.md` §12 says do not start it in the weeks before the trip.

### 3.12 The passkey has a detector but no selector — P3.1

The hard half landed: the tap-in detector reads the authoritative signal —
`TIER_LIMIT_REACHED` disappearing for every selected guest — and is wired into
the provider. The role half did not. You mark one target by hand, and the flag
only moves that target to the front of hits that had already matched the watch
list; nothing seeks out the earliest-returning eligible non-Tier-1 regardless
of rank. The passkey move is the one every guide leads with, and it depends on
getting *something* early rather than on getting the right thing.

_Where:_ `src/autopilot/priority.ts:47-57`, `src/autopilot/passkey.ts:11-20`.
_Size:_ medium. _Risk:_ `PLAN.md` §12 left this unscheduled on purpose — the
hand-marked flag substitutes for it, and a selector that books the earliest
thing regardless of rank is one bad morning away from spending a slot on a
filler. If it is built, it has to be bounded to the pre-redemption window and
to attractions you marked as acceptable.

### 3.13 What the learner learns does not survive to the next trip — ROADMAP item 12

**Built** — export in 1.3.0 and restore in 1.4.0. ROADMAP item 12 records how.

Every observation `observe.ts` records — and the plan, the party and the booking
log with it — lives in `localStorage` on Disney's origin, and nothing in `src/`
can get any of it off the phone. WebKit deletes all of a site's script-writable
storage after seven days of Safari use without a visit. The rehearsal manufactures
the learned drop times the main trip uses, weeks later.

_Size:_ small for an export, medium with a restore. _Where:_ a pure module beside
`src/autopilot/storage.ts`, and a button on Settings. _Risk:_ a backup must never
carry `auth` or `auth.persistence`, which hold a live Disney session, and a
restore must never write engine state or change dry run. ROADMAP item 12 has the
full treatment.

---

## 4. Decisions before code

**The first four were answered on 2026-09-15, three of them "leave it alone".**
The fifth was reopened on 2026-10-03 and is the only one waiting on a decision.
The items are kept with their reasoning rather than deleted, because each says
what would make the question live again — and because a decision recorded only
as silence gets re-proposed as a discovery.

### 4.1 ~~Should a NextLL search survive a tab switch?~~ — UX-PLAN §6.3. No

NextLL mounts its own engine, so leaving the tab stops the search. Hoisting it
would let a quick search keep running while you look at your plans. The cost
has grown since the question was framed: the action-lock ledger now means two
pollers would have to arbitrate the same per-attraction locks — the collision
class §1 used to carry as its Time Search item, fixed on 2026-09-14 by making
that search take the engine's lock rather than commit outside the ledger. That
fix is the pattern a hoisted NextLL would have to follow, and it is why this
remains a decision rather than a straightforward port.

**Answered 2026-09-15: leave NextLL as it is.** A trip is the wrong week to find
out how two pollers share a lock ledger. What would make it live again is the
trip being over, or the arbitration being settled by something other than a
park day on the main trip.

### 4.2 ~~Turn drop demotion on?~~ — P2.3. No

The machinery is built and switched off. Five of the nine attractions with
built-in drop times show no reliable pop-ups in public data, and bursting at a
dead time wastes requests at the minute they are worth most. The stated
precondition is recording coverage per scheduled drop time rather than per park
day, so both counts derive from the same evidence.

**Answered 2026-09-15: leave demotion switched off.** `DEMOTION_ENABLED` stays
false. The evidence it would act on is still gathered and still shown on the
Activity screen, so nothing is lost by waiting; and the store starts empty and
needs three covered days, so a short trip barely reaches the threshold anyway.
Demotion is the only part of drop learning that can remove a real burst target,
which is the wrong thing to be discovering on the main trip.

What would make it live again: coverage recorded per scheduled drop time rather
than per park day, so both counts derive from the same evidence, plus enough
observed days to mean something.

_Where:_ `src/autopilot/learned.ts:15-17,40-51,103-135`. _Size:_ medium.

### 4.3 ~~Will the party use Park Hopper?~~ — P3.4. Dropped

**Answered 2026-09-15: no work needed.** The party will hold Park Hopper, but
intends one park per day and does not want hopping
automated. So the distinction this item asked for — `TOO_EARLY_FOR_PARK_HOPPING`
carries a time and should schedule a poll, `TOO_EARLY_FOR_NEXT_PARK` has no
timer and should suppress cross-park targets — has nothing to act on: a plan
that never crosses parks never meets either code.

Kept rather than deleted, with the reasoning, because holding a Hopper and not
using it is not the same answer as not holding one. If a day does turn into two
parks, the two codes are still handled identically and the item is live again.
Nothing else depends on it: watch targets carry their own park and date since
P4.1, so a one-park-a-day plan cannot produce a cross-park attempt by accident.

_Where:_ `src/api/ll.ts:111-126`. _Size:_ medium, if it ever comes back.

### 4.4 ~~Should the live tier check run on a park day?~~ — P3.5. No

The tier bundle is fetched and the divergence warning exists, but the fetch is
gated so it never runs on a day-of poll — deliberately, because the bundle
appends closed attractions and the drop learner would read them as inventory.
Tiers moved twice in the last twelve months, and the main trip is exactly when a
stale flag would have the tool hold a Tier 1 slot for the wrong attraction.

**Answered 2026-09-15: leave the tier check as it is.** The fetch stays gated
off the day-of poll. The narrow version — fetch once at park open, use it for
the warning only, keep it out of the tip board the learner reads — is probably
right, and is what to build if this comes back; but it re-opens a path closed on
purpose, and the failure it guards against (a tier moving between now and
the main trip) is less likely than the one it would introduce (the drop learner
reading a closed attraction as inventory). The static flags were verified twice
and are correct today.

_Where:_ `src/api/ll/wdw.ts:176,246-265`. _Size:_ medium.

### 4.5 Should Autopilot weigh how a return time delays the next pick? — reopened

`PLAN.md` §9 listed a cascade model, scoring offers by how much they delay the
next booking, as refuted: the next selection opened two hours after booking,
whatever the return time. That was Genie+'s rule. Under Lightning Lane Multi
Pass the next selection opens when you redeem one or when its arrival window
passes (`PLAN.md` §2, checked 2026-10-03), so a late return holds a slot until
you ride it or its window passes, and `bookThenMove` taking a late time first is
no longer free.

**Open, and nothing is built on it.** The app does not depend on the old rule:
it reads when the next booking opens from Disney's tip board. What is open is
strategy: whether an earlier return should win over one better placed in the
window, and what a late first booking costs on a day with more targets than
slots. Decide before building anything.

_Where:_ how Autopilot chooses an offer (`src/autopilot/autobook.ts`) and Book
then move (`src/autopilot/automodify.ts`). _Size:_ a decision first.

---

## 5. Questions only the park can answer

`PLAN.md` §10 lists four. Three need a timestamped record that does not exist
yet, and instrumenting them is small work that has to land before the freeze or
it cannot be used at all.

1. **Does an expired, never-tapped first Lightning Lane free its slot?** Log
   the ineligible reason at the moment a window lapses. Until it is settled,
   treat an expected free slot as a hypothesis: try one offer, back off on
   `REDEMPTION_NEEDED` rather than burning the budget.
2. **Is tier release per-guest, and does it need a Tier 1 redemption?** Log
   `TIER_LIMIT_REACHED` before and after the first tap, ideally with a
   split-party tap-in.
3. **What is Big Thunder's post-reopening drop schedule?** Unmeasured. Let the
   learner run at approach cadence and see. This one does not need a park: the
   learner runs from home whenever the booking date is today (ROADMAP theme 2).
4. **Do the holiday overlay IDs still resolve?** See §3.3 — a data check, once
   the overlays are running.
5. **How long does Disney's itinerary take to show a change that has landed?**
   This no longer controls safety. An unresolved mutation does not clear on a
   timer or on repeated contrary reads; it clears only when Plans shows the
   exact requested result, a definitive late response arrives, or the user
   confirms what happened. The measurement is still useful for tuning the
   visible settling wait and the lease timings, but it must never become an
   automatic fail-open rule again.

   **Measure from the request leaving, not from a response arriving.** The
   obvious instrumentation — the gap between `book()` returning and the
   itinerary agreeing — measures the wrong population entirely: a commit that
   returned is a commit whose outcome is known, which is exactly the case a
   doubt never arises for. The interval that matters runs from the mutating
   request going out, or from its status-0, through to stable itinerary
   evidence. Log the send, log every subsequent plans read that does and does
   not show the change, and let the distribution of the ones that eventually
   appear set the window.

_Size:_ small, and it must be log lines rather than behaviour changes.

---

## 6. Testing and housekeeping

**The mutation-lifecycle gaps were closed on 2026-09-16.** Quarantined
reservations are visible in Activity and Plan Check, carry operation-specific
details, and have a two-step manual resolution after the user checks Disney's
Plans. Plan Check also warns when the browser lacks Web Locks rather than
silently degrading cross-tab exclusion. If durable quarantine storage fails,
the open page still blocks the reservation and says that the protection will
not survive a reload or coordinate another tab; the live renewal loop stops,
while its last lease record is left to expire normally rather than being kept
alive invisibly.

The named regression gaps are closed as well: `TimeSearch.tsx` has component
coverage for its mutation wiring, the real WDW client is tested forwarding that
control to both book endpoints, `daytimeline.test.ts` asserts the pure protected
span, and every durable/session storage key passes through a typed
`storageNamespace.ts` boundary. A source scan catches direct storage access and
handwritten namespaced literals, while notification tags have their own typed
`autoll3-*` namespace.

**Two audible overlaps are accepted until after the trip.** Several real finds
that arrive while the context is already running can schedule their chimes
together. A permitted **Test sound** press can also overlap a queued real alert
that recovers in the same turn. In both cases the user hears extra sound rather
than losing an alert, and the diagnostic case necessarily has the user looking
at the phone. Deduplicating either would add shared delivery coordination to the
alert path that has just been stabilised, so both remain deliberately out of
scope for the freeze.

**The volatile quarantine is under-tested, as of 2026-09-17.** A review of
`787cff3` raised seventeen surviving findings and only two were defects; the
other fifteen were paths that can be deleted with the whole suite green. Four of
the most load-bearing were closed the same day — `renew()`'s quarantine gate,
`reconcile()`'s volatile pass, `resolveDoubt`'s volatile clear, and the shared
attraction-name rule. These remain open, all in the mechanism added that week:

- `activeVolatileQuarantine()` prunes the page-local store destructively on
  every read and nothing tests the predicate that decides what it drops.
- Promotion of a page-local doubt to durable protection, once storage recovers,
  is untested.
- `subscribeQuarantine`'s cross-tab `storage` listener has no test.
- `loadQuarantine()`'s deliberate swallow of a read failure has none either; its
  removal crashes Activity rather than failing a test.
- `settle()` in the provider's `finally` is the only thing stopping a deadline
  timer quarantining an already-successful mutation, and nothing covers it.
- The `return result.durable` both foreground search screens added is
  unverified: deleting it from both leaves the suite green.
- `TimeSearch.test.tsx` never pins *which* reservation the screen locks, so a
  wrong lease key would pass.
- `volatileQuarantine` is module state `beforeEach` cannot reset, so tests that
  touch it must clean up in a `finally` — three now do, by hand.

None is a known defect. They are places where a future change would break
something silently, which in this subsystem is the shape that has cost the most.

**The harness misses three things, as of 2026-10-03.** Its fake LL client never
runs the booking-response reader in `wdw.ts`, so a harness run cannot catch a
reader that refuses a real answer. Its first screen is a wrapper around Home
rather than Home itself, so after a hand Change succeeds there, going back to
Home fails ("No previous Tabbed screen"), which it does not on the phone. And
the fake offers a move at the time already held, so the Live engine scenario
never shows the Haunted Mansion move its description promises. Separately,
`client.ts` still catches a dispatch error that `fetchJson` never throws.

**One thing that pass established, worth keeping:** jsdom does no hit-testing,
so a test that "clicks through" an overlay passes with the overlay bug present.
Where the fix is a CSS property, assert the property; a behavioural test there
is a test that cannot fail.

**Nine Dependabot pull requests are open and none should be merged in a
hurry.** `.github/dependabot.yml` sweeps npm and GitHub Actions weekly. Seven
date from 2026-09-09; #30 (vite 7→8) and #31 (`@vitejs/plugin-react` 5→6)
arrived on 2026-09-16 and are two more majors on the toolchain that builds the
shipped bundle, so they belong with #9 rather than with the merge-now item. The
plan, decided 2026-09-15 and re-checked 2026-09-17:

**Also worth knowing, and not recorded when this section was written:**
Dependabot's *security* half is switched off for this repository — only version
updates are enabled. So these PRs only ever say "a newer version exists", never
"this one is vulnerable", and no alert will fire before the trip. The
compensating control is real (`npm audit --omit=dev` is 0, and only `react` and
`react-dom` ship), but the signal is absent rather than quiet.


- **Merge now:** #7, jest 30.0.5 to 30.5.1. A patch bump on the test runner, and
  the only one where deferring buys nothing.
- **Close:** #9, TypeScript 5.9.2 to 7.0.2, the one red check. TypeScript 7
  removed `baseUrl` and forbids non-relative `paths`, and `tsconfig.json` uses
  both (`TS5102`, `TS5090`); the fix is to drop `baseUrl` and write
  `"paths": {"@/*": ["./src/*"]}`. Worth knowing that `tsc` never compiles the
  shipped code here — `build` is `vite build`, and `tsc --noEmit` is only the
  gate — so this changes what the gate catches, not what reaches the phone. That
  gate is still the only typecheck there is. A brand-new major three months
  before the trip is not worth it; Dependabot reopens it when someone is ready.
- **After the trip:** #5 `@eslint/compat`, #6 `@testing-library/jest-dom` and #8
  `@tailwindcss/vite`. #8 is the only npm bump with a user-visible surface — it
  generates the shipped CSS — so it wants a harness pass at 360 px rather than a
  merge on green CI.
- **After the trip, and one at a time while watching:** the four Actions bumps.
  #1 `checkout` and #3 `setup-node` are already partly stale, since `check.yml`
  and `deploy.yml` moved to v5 after these were opened and only
  `data-freshness.yml` is still on v4. #2 `upload-pages-artifact` and #4
  `deploy-pages` touch **only `deploy.yml`**, and `deploy.yml` runs on push to
  `main` — never on a pull request. Their green `check` therefore says nothing
  about them at all, and merging either is an unverified change to the two steps
  that publish the build. The deploy gates independently, so a failure leaves
  Pages serving the build already on the phone rather than breaking it; the cost
  is debugging a publish pipeline instead of booking Lightning Lanes.

Worth considering separately: moving the schedule to monthly, or pausing it
until January. Standing PRs nobody intends to merge make a red check stop
meaning anything.

**The port back to AutoLL v1.1 has not started.** Phase 1 deliberately kept the
new work in new files so the port would be cheap, and none of them exists in
that repository yet. AutoLL is the frozen build that still works if this one
breaks, and today it has none of the day's-work screens. The plan's own rule is
to port only after park use, so it cannot honestly start before the trip — and
the Walt Disney World narrowing must not be carried across.

---

## 7. Decided against — do not rebuild

These were considered and rejected with reasons. They are recorded so the same
idea is not proposed again as a discovery. The full arguments are in `PLAN.md`
§9 and `UX-PLAN.md` §8.

**Data and ranking.** A party-night date table for the Christmas Party and
Jollywood Nights — the 90-minute drop horizon already bounds the case, and a
wrong date silently suppresses real drops on an ordinary day. Deleting
DINOSAUR, removing TRON's priority, inventing one for Space Mountain, swapping
Frozen Ever After and Remy, swapping Tower of Terror and Toy Story Mania,
re-ranking Glimmering Greenhouses, demoting Jingle Cruise. A test asserting
every Tier 1 carries an average wait.

**Engine.** A day's action allowance — removed outright on 2026-09-14, and it
should not come back as a count of bookings. The cap's stated reason was that
"every action consumes a real entitlement", which is false: Disney counts a
*redemption*, not a booking, so an attraction can be booked, cancelled and
rebooked all day at no cost to what you may hold. `resolveBook`'s own comment
said so while the allowance contradicted it. What is genuinely one-way is a
*modify* or a *swap* — each gives up a held return time that may not come back —
and a day-count was a poor instrument for that: it let the harmless, frequent
kind (bookings) spend the budget, then locked out the booking the user actually
wanted. A runaway *request* loop was never its job either; `RateLimit(5)` and
its five-second cooldown exist for that and say so. If the one-way risk needs
bounding, bound moves and swaps on their own terms — see §3.7, which is the
honest version of it. (A cascade model scoring offers by how much they delay
the next booking was listed here too. Its refutation rested on Genie+'s two-hour
rule, and it is open again as §4.5.) Rejecting offers that land after park
close — Disney does not sell them, so the guard is a no-op. Feeding learned drop
times into the Tier 1 hold — a false positive costs a wasted request in the
cadence and a forfeited Tier 1 in the hold. A Tier 1 guard on the future-date
path — the obvious guard deadlocks, because the hold only avoids deadlock when
the better attraction has a drop still ahead *today*.

**Screens.** "Suggest a safe window" on the timeline, and editing the timeline
in place — both would put a second opinion beside the booker's own predicate. A
sticky active-search banner across screens — it would describe something that
cannot be running.

**Scope.** Disneyland support and virtual queues. Scraping paid tables into the
repository. Anything whose purpose is to obtain more entitlements than Disney's
published rules allow.

**Recorded 2026-09-23.** Running as a Home Screen web app — it would dissolve
three problems at once, with notifications as a second alert channel, no Safari
toolbar to guard and storage exempt from the seven-day cap, but AutoLL-6 has to
run on Disney's own origin to use the Disney session, and a Home Screen web app
sends navigation outside its scope back to Safari. Autopilot booking every day of
a stay on its own on the booking morning — the engine is built around one booking
date, and rebuilding that before the main trip is the riskiest change available
(ROADMAP item 15). Restoring engine state or dry run from a backup — engine state
describes reservations at one instant, and dry run is silently wrong in either
direction (ROADMAP item 12).

---

## A suggested order

Retired 2026-09-23. `ROADMAP.md` now carries the calendar, and two documents
keeping two orderings is how both drift: this table ranked expiry rescue first and
the countdown between the trips, while the roadmap now puts the lapse warning ahead of
rescue and has repriced the countdown down. Follow the roadmap.

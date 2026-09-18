## A desk for the gym, fenced by two attributes — 2026-09-18

**"Add an adaptive desktop layout to the app, for gym staff only. Do not change
the existing mobile experience."** At 1024px and wider, with a real pointer, a
staff member now gets three columns: the navigation rail on the right, the
club's day in the middle, and a "דורש תשומת לב" rail on the left. Everyone else
gets exactly what they had.

**What "everyone else gets exactly what they had" means, as a mechanism rather
than a promise.** Two attributes land on `<html>`: `data-layout="desktop"` when
`(min-width: 1024px) and (pointer: fine)` matches, and `data-staff="1"` when
that AND `is_staff()` are both true. Every rule in the shell is prefixed with
**both**, and there is deliberately **no rule keyed on `data-layout` alone** —
so a member at a laptop matches nothing at all. A test walks the stylesheet and
fails on any selector missing either half. A browser check at 1440px measures
the member's sidebar at 248px/x=892 and their logging column at 560px/x=300,
the same numbers that block has produced since the ≥900 tier shipped.

`(pointer: fine)` is half the query and does most of the work: a 1024px tablet
in landscape is wide enough for three columns and completely wrong for them.

**It adds no colours, no fonts, no tables and no screens.** Every value in the
new CSS is an existing token, so the shell follows the theme through both dark
mechanisms without a rule of its own — there is nothing to duplicate into them
because there is no literal colour to go stale. Every panel in it is a section
renderer that already existed, and the week strip comes from
`club_wod_boards(p_from, p_to)`, which has taken a date range since the day it
was written. One destination was added — לוח המכון — as one more row in the
registry the bottom bar and the hamburger already read, rather than as a second
navigation mechanism.

**The sidebar groups what was already there.** צוות, קהילה, האימון שלי, built
from the same `getNavItems()` config the bottom bar uses, with the grouping
read by that one surface and nothing else. A member's sidebar renders from the
identical branch it always did, which is asserted by hashing its HTML.

**The 560px logging column still never changes width.** That rule has its own
long argument in the stylesheet and it survived this: only the staff-home tab
widens, and a coach on the logging tab measures 560px in a real browser.

**This replaced a first attempt that was reverted the same day.** That version
assumed React, added a `role` column the schema already had six better answers
for, shipped a migration with a new table and new policies, hardcoded 23 hex
colours with no dark half, and named its detection function `useIsDesktop()` in
a repo with no React. None of it had reached production. The audit that found
all of it is in the branch history; the lesson worth keeping is that a brief
written without the repo in front of it will confidently ask for the thing the
repo already has.

**Also here:** `DESIGN_HANDOFF.md`'s token table had `--energy` at `#C94B29`
and `--brass` at `#956529`. Both had moved — to `#E85D3D` when Direction 06
unified the accent across themes, and to `#8a5d25` after an axe pass caught
`.chip-btn.selected` at 4.35:1 on `--surface2`. The table now says what ships,
and says why each moved.

## The admin panel asks again — 2026-09-15 (ninth entry)

**"On ניהול מערכת there is need to be separate log in for admin, because this
is the area for that."** Tapping the admin panel now asks for the password a
second time, even for an account already signed in as admin. Not a collapsed
section either - the bug inbox, the audit log and the module toggles are not
in the DOM at all until it is answered.

Fifteen minutes, then it re-locks. Checked on every render rather than on a
timer, so a phone that was backgrounded is locked the moment it is looked at
again. **Held in memory only** - never localStorage, never sessionStorage -
because persisting it would defeat the exact thing it exists for: this guards
an already-unlocked phone, and a token that survives a reload hands the panel
over anyway. Cleared on sign-out too, or the next person to sign in on the
device inherits an open admin panel.

A wrong password leaves the gate up and **does not sign you out**. Losing a
session to a mistyped password would be a worse outcome than the one this
prevents. The failure message is the same for a wrong password and for a
failed request, because an error that distinguishes them tells someone
probing the device which half they got right.

**What this is not, stated in the code and in the tests.** It is not the
security boundary. `is_admin()` in the database is, and it is re-checked on
every action regardless of this flag - nothing client-side can grant a
non-admin anything. This guards the PHYSICAL-ACCESS case: an unattended phone
in a gym, a head coach who also holds admin, a member handed the device to
look at a photo. Saying so plainly matters, because a lock described as more
than it is becomes the reason nobody adds the real one later.

Verification uses `signInWithPassword` against the SAME account - the standard
step-up shape, since Supabase has no "check this password without a session"
call. Deliberately not a stored hash or any client-side comparison: the
password stays in `auth.users` and this app holds no second copy of it.

**The gate broke thirteen tests that reach admin surfaces, and they were fixed
honestly rather than bypassed.** Each seeds a credential on its mock and
submits the real form, through two helpers in `test/helpers/boot.mjs`. A test
seam that skipped the gate would mean the lock is never exercised on the path
the other sixteen hundred tests take, which is how a lock quietly stops
working. One test title was also corrected: it still claimed the audit view is
gated on `community.analytics.view`, which stopped being true earlier the same
day when 202609150004 moved it to `is_admin()`.

**And a decisions ledger.** `docs/audit/RESEARCH_DECISIONS.md` records what
happened to each of the ~70 recommendations from the eleven-agent research
pass: built, declined by the owner, refused on the research's own reasoning,
or still open. Three items were closed by the owner this session - streak
consolidation, opt-in board ranking, and finishing the `lang="en"` tagging -
and they are written down for one reason: an unrecorded "no" gets re-proposed
by the next pass, researched again, and argued again.

Verified: npm test 1687/1687.

---

## Two jobs, two screens: the admin and head-coach panels split apart for real — 2026-09-15 (eighth entry)

The owner opened the admin panel on a phone and corrected the design in one
sentence: **"head coach will add users and run the club, admin runs only
app."** That is a cleaner division than the one shipped this morning, and it
invalidates it.

The first split made the admin panel a SUPERSET - every club area plus the
admin ones - reasoning that an admin should never have to switch screens. The
correction is better because a superset is invisible: a screen containing both
jobs does not look like a separation, it looks like the old screen with more
on it. Two named doors, each landing on the panel it names, is what makes the
division legible.

**The panels no longer overlap at all.** The head coach gets adding members,
the roster and club health, moderation and restrictions, the club's own
numbers, and the onboarding content a new member reads. The admin gets the bug
inbox, the audit log, the module toggles that decide which features exist, and
role/password control. The admin panel's third tab is renamed "האפליקציה",
because that is what it now is. An admin who wants to invite someone goes
through the club door - which they have, because an admin is also staff and
gets both hamburger rows.

**The bug inbox stopped hiding.** Reported directly after first use: "it need
to tap טעינת דיווחים for seeing it, so its not good." It now loads itself when
the panel renders and opens expanded. Lazy-loading behind a button was right
while this sat among five collapsed areas on a screen shared with the head
coach; it is wrong now that the admin panel exists largely to show it.

**And admins are told when a report arrives** (202609150005). An AFTER INSERT
trigger on bug_reports notifies every admin immediately - not batched, because
a member telling you the app is broken for them is the wrong thing to sit on
for six hours, and notif_create()'s own 1-hour de-dupe still collapses a
burst. Deliberately admins ONLY and not mod_alert_recipients(), which includes
coaches: closing a report is is_admin() gated, so alerting someone who cannot
action it is an interruption with no available remedy. Three assertions cover
exactly that - the admin is notified, a coach is not, and the reporter is not
told about their own report.

**The reconciliation cost, stated plainly because it was mis-reported once
already.** The restructure broke **117 tests across 16 files**, not the six
first reported here - six was the number visible in the first screenful of
output, and counting before reporting would have been the right order. Most
were mechanical: a test reaching a club surface now goes through the club row,
resolved by one pattern that works for both fixture types. Six needed
judgement:

* **"every section is still reachable"** keeps its guarantee and now sweeps
  BOTH panels. Sweeping one would report a false loss for sections that simply
  moved.
* **The audit-log tests** were first dragged onto the club row with the rest of
  their file, which broke four of them, because the audit log is the ADMIN's -
  a record of staff actions is not something the recorded staff should be the
  ones to read. They have their own helper now, with that reasoning beside it.
* **The jump row** is scoped per panel. A chip that scrolls to nothing is
  exactly the "button that goes nowhere" that row was built to prevent.
* **The "admin panel is a superset" test**, written hours earlier in this same
  session on reasoning the owner then corrected, now asserts the opposite: the
  admin panel carries the app areas and must NOT duplicate the club's,
  including no invite or member tabs. The division is encoded where it cannot
  quietly drift back.

Verified: npm test 1683/1683, supabase test db Files=112 Tests=3455 PASS.

---

## A scaled PR says so, and a recommendation that was wrong for this codebase — 2026-09-15 (seventh entry)

**The PR flash now names the level.** `bestWodScore(id, excludeId, rx)` has
always kept an Rx ladder and a scaled ladder apart, so a scaled athlete's
personal record has always been a real record in the data - which is better
than Wodify, where only Rx metcons can be PRs at all. The screen never said
so: the same "שיא חדש!" appeared either way, leaving a scaled athlete to
wonder whether the app was humouring them. It now reads "שיא אישי מסוקיילד!"
- named as a fact, not parenthesised, because a bracket reads as an asterisk
on the achievement.

The research behind this is consistent and runs both ways: scaled athletes
read an unmarked board as "everyone else did the real one" and stop logging,
and competitive athletes suppress honest scaled results to protect a board
position. Both end in a thinner log, and every other feature here - the
achievement engine, the coach dashboard, the club board itself - is built on
the log.

**And a recommendation that turned out to be wrong for this codebase, built
and then backed out.** The same research pass recommended splitting the club
WOD board into Rx and scaled lanes, on the stated premise that it renders
"one list where Rx rows carry a badge and the rest are bare". It was built
that way, and an existing test caught it: *"nothing ranks: no position, no
sort, and the ranked conventions are not borrowed"*, which defends the
board's promise to render in arrival order, full stop.

Two things were true on inspection, and both are worth recording:

1. **The premise was false.** `renderClubWodResultRow()` already pushes
   `effortHtml(r.rx ? "rx" : "scaled")` for EITHER value, and `effortHtml()`
   renders both through identical markup off one display map. Both levels
   were already named with equal weight. There was no asymmetry to fix.
2. **The fix cost something real.** Grouping is not ranking - it used
   `filter()`, never `sort()`, and computed no position - but it is still
   reordering, and this board was deliberately built to be unable to become a
   leaderboard. That guarantee is worth more than a fix to a problem that was
   not there.

Reverted in full. `test/scaled-parity.test.mjs` now asserts what is actually
true - that both levels already go through one helper, and that the board
still renders unsplit in arrival order - so the same recommendation does not
get rebuilt from the same false premise later.

Two mis-targeted edits were caught by tests rather than by review, which is
the argument for writing the test first: the label hook landed on `#prFlash`
(the STRENGTH flash, driven by a different function that knows nothing about
rx) instead of `#wodFlashBox`, and the flash fixture needed
`choosePickedWod()` because `renderWodLogSection()` early-returns until a WOD
is actually chosen.

Verified: npm test 1683/1683.

---

## Hebrew grammar the app had been getting wrong, and the recent chips become buttons — 2026-09-15 (sixth entry)

Eleven research agents read eleven competitor products. The most valuable
thing they produced was not a feature: it was **five defects in this app's own
code**, four of which were verified directly before anything was changed. Two
were regressions from this morning's own migrations and shipped in the
previous commit. Three were Hebrew, and they had been wrong since the copy was
first written.

**`ברוך/ה הבא/ה` cannot be written that way.** Masculine `ברוך`, feminine
`ברוכה` - the `ך` has to BECOME `כ`, so no slash can join them. It is a
non-word in both directions, and it was the first string a new member ever
read. Patching it to `ברוכ/ה` would still be wrong, so it is replaced with a
construction that sidesteps gender entirely: `שמחים שהגעת למועדון`.

**The general rule underneath it is the more useful finding.** In unvocalized
Hebrew, 2nd-person past-tense verbs are homographs across gender - `נרשמת`,
`סומנת`, `הגעת`, `בחרת` are each already both. This app was adding `/ה` to
words that were already neutral, and the slash made them *wrong*: `נרשמת/ה`
resolves to `נרשמה`, which is THIRD person feminine. A person mismatch, not a
gender fix. Three of those removed.

**Nineteen slash forms were missing the masculine final-form letter** -
`משתתפ/ת` where the masculine is `משתתף`, and likewise `מעוניינ/ת`,
`מפרסמ/ת`, `הצטרפ/ה`, `עודכנ/ה`. Spelling errors, not a compression
convention.

**And forty-five Hebrew abbreviations used an ASCII double quote** rather than
the gershayim `״` (U+05F4). Three independent reasons this matters, only one
of them typographic: U+05F4 is bidi class R (strong RTL) while `"` is a
NEUTRAL, and a neutral inside a Hebrew word next to a number run is exactly
what strands during bidi resolution; `esc()` turns `"` into `&quot;`, which
makes the bidi run-finder see a Latin word `quot` inside a Hebrew word -
`safe-helpers.js` documents computing run boundaries pre-escape specifically
to route around that, and the gershayim removes the hazard instead of routing
around it; and CLDR agrees, since `Intl.NumberFormat("he-IL")` emits `ק״ג`
itself. A new test file fails the build if any wrong form reappears.

**The recent-entry chips are now buttons.** They already existed and were
read-only decoration: a member could see they squatted 100x5 on Sunday and
then had to dial 100 back in by hand, about 32 taps of a 2.5kg stepper from
the default. Tapping one now fills weight, reps and sets. This is the single
mechanic Hevy and Strong both build their entire logging loop around, and it
suits this app better than theirs - we log AFTER training, so the member is
reconstructing a session they have already done, and a recent value is the
most likely value. Duration entries stay inert on purpose: they carry no
triple to copy, and a button that silently does nothing is worse than a label.

**`lang="en"` on the bidi wrapper**, so a screen reader stops speaking `Rx`,
`WOD`, `AMRAP` and every movement name through the Hebrew voice. Recorded
honestly as PARTIAL rather than done: the research called this a one-string
change, but the wrapper only fires for runs containing an interior neutral
(`Back Squat 100`), so a bare `Fran` still takes the unwrapped path. Covering
those means wrapping every Latin word in a span, which is a real DOM-cost
change and belongs behind the render-cost trip-wire rather than smuggled in
here. Twenty-one assertions pinned the old markup; their strip patterns are
widened to accept any attributes, so they still check losslessness rather than
exact markup.

**The moderation sheet's destructive primary said `אישור`** - literally
"Confirm", which makes the member re-read the title to learn what they are
confirming at the moment they are deciding whether to. It now repeats the
title's verb+noun, matching the sibling ghost-reclaim sheet in the same file
that already did this correctly. Its dismissal moved from `ביטול` to `חזרה`
for a reason English does not have: the restrictions panel beside it uses
`ביטול ההגבלה` to mean REVOKE the restriction, so `ביטול` next to
`הגבלת פרסום קבועה` genuinely reads two ways.

Verified: npm test 1679/1679.

---

## The support sheet closed the moment you tapped it — 2026-09-15 (fifth entry)

Reported from the phone within hours of shipping: "trying to put text it
closes page." The support sheet dismissed itself the instant a member tapped
the description field, which made the bug-report feature - the one built
specifically so members could report bugs - impossible to use on a touch
screen.

**One missing line.** `#supportOverlay` carries
`data-action="close-support"` so a tap on the dim backdrop dismisses it. The
click handler resolves an action with `e.target.closest("[data-action]")`,
which walks UP the tree from whatever was tapped. Nothing inside the sheet
carries its own `data-action`, so a tap on the textarea walked up, found the
overlay, and closed the dialog. Every other overlay-level close in this file
already guards against exactly this - `close-settings`,
`close-notifications` and `close-nav-menu` each carry
`if (el.id === "<overlay>" && e.target !== el) return;` - and this one was
written without it.

Two regression tests, because a fourth missing guard is the obvious next
instance of this: one behavioural (tap the textarea, the sheet stays open;
tap the backdrop, it still closes - the control matters, or the fix could
have removed the only way out of the dialog) and one structural, asserting
that all four overlay-level close branches carry the guard by name.

**Also, the admin now gets BOTH hamburger rows.** The first pass gave an
admin a single row, reasoning that their panel is a superset so a second row
would be a second door into the same screen. On the actual phone that read
as "there is no club owner section" - which is the honest reaction, because
a superset is invisible. Two named doors, each landing on the panel it
names, is what makes the separation legible. The admin row keeps the
moderation badge; the club row does not duplicate it, since it is the same
queue counted once.

Verified: npm test 1672/1672.

---

## Two panels, not one: the admin screen and the head-coach screen split apart — 2026-09-15 (fourth entry)

The club owner asked for an admin panel and a head-coach panel in the
hamburger, each with its own login, and for bug reports to be collected in
the admin one. The research finding first, because it shaped everything else:
**most of it already existed.** "ניהול" was already a staff-gated tab with
invites, roster, moderation, audit log, club modules, analytics and the
onboarding editors; the RBAC already had six ranked roles with head_coach at
30 holding announcements, challenges, comment moderation, pinning, events,
member restriction and delete-any-post. What did not exist was somewhere for
bug reports to land, a way to reach any of it from the hamburger, and a
separation between the two audiences.

**The hamburger genuinely did not have it.** `renderNavMenuList()` renders
`renderNavRows(true, true)` - onlyOther=true, which by design lists only
items NOT in the bottom tab bar - and the manage entry was `main: true`. So
on a phone it sat in the bottom bar and appeared nowhere in the hamburger,
which is where someone goes looking to manage things. Both panels are now
`main: false`, which moves them into the hamburger through the existing
registry rather than a second navigation mechanism, and hands the sixth
bottom slot back to the five member tabs.

**Bug reports now have somewhere to go.** New `bug_reports` table with a
three-way boundary: any member files, a reporter reads back only their own,
staff read all, and admin alone changes status. The reporter's read goes
through a function whose RETURN TYPE has no `admin_note`/`handled_by`, so the
column-exposure failure round 10 had to fix on two moderation tables cannot
recur here by construction rather than by policy. The support sheet files to
this inbox FIRST and falls back to the WhatsApp/mail handoff on any failure -
never the reverse, because the handoff is the reliable path (it needs nothing
but the device) and the inbox is the useful one (status, history, a second
admin who can see it was handled). It never reports a success it did not get.

**The split follows what the database already enforced, then widened it to
match.** The head coach's panel is the club: invites, roster, moderation,
club modules, onboarding content and the club's own numbers. The admin's is a
superset - all of that plus bug triage, the audit log, role changes and
password resets - so an admin never switches screens for a club task. Four
permissions moved to head_coach so the panel's controls are backed by real
grants instead of rendering and then failing on use. 202609030008's narrowing
(minting a COACH-role invite needs is_admin specifically) is untouched and
still enforced inside `invite_create`, not in the grants table.

**And the widening caught a real defect that had nothing to do with this
feature.** `admin_actions_page()` - the audit log - was gated on
`has_perm('community.analytics.view')`, not on being an admin. This file's
own header comment asserted the opposite when first written, and 0085's
existing assertion is what proved it wrong: granting head_coach analytics so
the club panel could show the club's numbers silently handed them the record
of every staff action, including their own. An audit log the recorded staff
can read is not an audit log. The permission was doing double duty - it
legitimately gates five analytics readers plus the monthly recap, all
club-running surfaces - so the fix re-gates the log itself on `is_admin()`
rather than withholding analytics. Behaviour-preserving for everyone who had
it before: `analytics.view` was seeded only to admin (rank 50) and owner
(60), both of which `is_admin()`'s `role_rank >= 50` covers. The only caller
that loses access is the head_coach grant added in the same migration, which
had not shipped.

**Accounts, created in Supabase and not in this repository.** The club's
admin signs in with a real address so Supabase's own password-reset mail
works for it - "ask an admin to reset it" has no answer when the locked-out
person IS the only admin - and `login()` now accepts an email as well as a
username to allow that. Account CREATION stays username-only on the
non-routable `.invalid` domain, which is what lets this club hold no member
email addresses at all; a test asserts that widening login did not leak into
signup. A bootstrap migration grants the two roles, guarded by email match so
it is a no-op on any stack where those accounts do not exist, and carrying no
password - the accounts were made through the ordinary signup endpoint and
their credentials live only in `auth.users`.

Four defects were caught by verification rather than by review, three of them
by simulating the accounts that do not exist locally (so "the migration
applied cleanly" had been meaningless): `admin_actions.actor_id` does not
exist (it is `admin_id`/`action_type`), both of that table's closed
vocabularies needed the new values, `invite_redemptions.invite_id` references
`invite_codes` while `person_invite_id` references `invites` - the names
invert what you would guess - and there is no `community.pins` permission
despite the string appearing in older migration prose, which failed the whole
grant insert on a foreign key.

Verified: supabase test db Files=111 Tests=3452 PASS, npm test 1670/1670.

---

## A support inbox, and the loop guard that stopped sanitize_upload shipping broken — 2026-09-15 (second entry)

Follow-up to the real-phone session earlier today. Three things were left
open at the end of it; two are closed here and the third is a one-command
handoff.

**The support sheet now routes somewhere.** `supportEmail` is set to the club
inbox, so "דיווח על תקלה" hands a composed report to the member's mail app
instead of only offering the clipboard. Deliberately the CLUB address and not
a personal one: `cloud-config.js` is committed and served to every browser, so
anything in it is public by construction, exactly like the publishable key
beside it - which is fine for an address whose entire job is to be written to.
`supportWhatsApp` is still empty; setting it is one more line whenever the
club wants that route too. A new test reads the shipped config directly and
fails if BOTH channels are ever empty, because a support screen whose only
route is "copy this somewhere yourself" is a feature in name only and its
failure mode is silent - nobody notices an inbox that never receives.

**sanitize_upload was about to be deployed with an unbounded trigger loop.**
Found while reading it one last time before pushing it live, which is the only
reason it was caught: `202609110003`'s trigger fires `after insert OR UPDATE on
storage.objects`, and the function's own sanitized re-upload IS an update to
storage.objects. So the real sequence was upload -> trigger -> sanitize ->
update -> trigger -> sanitize -> update, with no terminating condition, since
a re-upload bumps the row whether or not the bytes changed. Every photo posted
to the club would have become an endless cycle of Edge Function invocations
and Storage writes on production. The function had never run anywhere: it was
never deployed, and the trigger is inert locally because the Vault secrets are
placeholders on every local stack, so no test and no environment this repo has
ever had could have surfaced it.

The guard is a **fixed point, not a flag**: `sanitizeImageBytes()` strips
metadata segments, and bytes with none left come back unchanged, so the second
pass over an object this function already wrote produces output identical to
its input. Skipping the write in that case ends the loop after exactly one
extra invocation - no marker to store, no metadata to keep in sync, and no way
for the guard to drift out of agreement with the sanitizer, because "already
clean" is defined as whatever the sanitizer itself declines to change.
Explicitly not done with a stored flag (forgeable by the same direct Storage
write this function exists to backstop) and not by narrowing the trigger to
INSERT only (that would reopen avatar re-uploads, the exact case the
migration's own comment says UPDATE was added for).

Idempotence is now asserted rather than assumed - six new tests in
`test/security-hunt-image-sanitize.test.mjs`, one per format, each paired with
a non-vacuity control proving the FIRST pass really did strip something, so
"the second pass changes nothing" cannot pass by accident on a fixture with
nothing to remove. Those tests are load-bearing for availability and cost, not
just correctness: if idempotence ever breaks, the guard silently stops
terminating and the loop returns.

**`sanitize_upload` was also the only Edge Function in the repo with no
`deno.lock`** - the other three have one and `test.yml`'s
`edge-function-lockfiles` job runs `deno cache --frozen --lock=deno.lock`
against every function directory, so that gate could not have passed for it.
Added. All four lockfiles are byte-identical (same md5) because all four
resolve the same single remote import, `@supabase/supabase-js@2.57.4`;
sanitize_upload's second import is a local relative path, which is not locked.
Copied rather than generated, because deno is not installed in this
environment - the CI job is what will verify it independently.

**Still not deployed.** The function is fixed, tested and lockfiled, but
`supabase functions deploy sanitize_upload` was refused by this environment's
permission layer, twice. Until someone runs it, the trigger added this morning
keeps POSTing every avatar and post-photo write to a 404 - harmless in itself,
since `net.http_post` is fire-and-forget, but the server-side EXIF/GPS
stripping and magic-byte content-type check that migration exists to provide
are not running while the repository reads as though they are.

Verified: full suite 1665/1665, check-version / check-vendor-version /
migration-immutability OK. Browser-check not re-run this pass and that is
stated rather than glossed: nothing in `app.js`, `cloud.js`, `index.html` or
`sw.js` changed here - the diff is `cloud-config.js`, one Edge Function, one
lockfile and two test files - and the suite was 44/44 on the commit
immediately before this one.

---

## The first real phone: four reports, one root cause, and a way to report the next one — 2026-09-15

Every audit in this repository has said the same thing about its own biggest
gap: no device has ever run this app outside Chromium. That finally happened
today, on an installed iOS PWA, and it produced four "not working" reports in
three minutes - more than the last several automated passes combined.

**Three of the four were not broken.** That is the finding, not an excuse.
Every one of them had its explanation parked in a `title` attribute, and a
touch screen has no hover, so a correctly-disabled control and a dead control
are the same object to the person holding the phone. A `title` is a desktop
affordance and this is a phone-first app; the codebase already knew that -
`renderMedal()` carries a comment saying so in as many words - and had simply
only ever applied the lesson in one place.

- **The medals screen.** Reported as the earned Squat bronze plate being lit
  but unlabelled, next to a locked Deadlift bronze that explained itself in
  full. The caption was `earned ? "" : rule`, so the one medal the athlete had
  actually won was the only one on the page with no text under it. Exactly
  backwards - the rule is the record of what you did to earn it, and it is
  most worth reading once it is yours. Now printed for both states. A test
  asserted the old behaviour ("an earned badge should not show its unlock rule
  as a caption"), so the defect was the contract; that assertion is inverted
  with a comment explaining what it used to require.
- **"שחרור ההזמנה" in admin.** Correct: the invite had stalled 6 days against
  a 7-day grace period, so `disabled` was right. The "עדיין בתהליך" tag said
  the state but never the rule, and the rule - come back tomorrow - was
  hover-only. It now says how many days are left, on screen.
- **"סימון הכול כנקרא" in notifications.** Also correct: every loaded row was
  already read. But a disabled `.link-btn` is a 13px steel underline at
  opacity .45 sitting beside an identical-looking enabled "סגירה". The dead
  control is gone; the fact ("הכול כבר סומן כנקרא") is there instead.

**The fourth was real, and it was all four photo uploads, not one.** Every
file input in the app - avatar, composer, PR photo, club WOD - hid itself with
`display:none` inside a wrapping `<label>`. A `display:none` input is not
rendered at all, and Safari, notably inside a standalone PWA, does not
reliably forward a label activation to a control that is not in the layout:
the picker never opens and nothing errors. Replaced with a `.file-input-hidden`
helper that keeps the input in the layout and merely invisible (clipped, 1px,
absolutely positioned), which is the portable form of this pattern. Pinned by
a test that fails on any future `display:none` file input.

**And the reason all four nearly went unrecorded: this app had no way to
report a bug.** They reached a developer only because the person holding the
phone was one. A new "תמיכה ודיווח על תקלה" row in Settings › עזרה opens a
sheet where a member describes what happened, sees exactly which device facts
will travel with it, and hands the report to WhatsApp, to mail, or to the
clipboard.

Three decisions worth stating, because each was a fork:

1. **It lives in `app.js`, not `cloud.js`.** Community is opt-in and the
   training log needs no account, no network and no Supabase. A member who
   never joined is exactly as entitled to ask for help - more so, since the
   offline log is the part they use daily. Putting it in the community layer
   would have made "can I report a bug" depend on having said yes to a social
   feed.
2. **It hands off rather than writing to a table.** Reporting a bug is
   precisely the moment the app may be the broken thing, and a table write
   needs a live client, a network, a valid session and an intact RLS path -
   four things a bug report must not be gated on. Composing locally costs none
   of them, works in airplane mode, and leaves the member holding their own
   copy. WhatsApp is also this club's real channel, by its own research.
3. **The diagnostics carry the device and nothing else** - version, installed
   -as-PWA, online/offline, whether Community is on, user agent. No name, no
   handle, no training data. It is rendered on screen rather than attached
   invisibly, because a report that quietly ships facts about someone's phone
   without showing them is not something this app should do. A test seeds real
   movements and weights and asserts none of it can reach the report.

`supportWhatsApp` / `supportEmail` in `cloud-config.js` are both empty, so
**no channel is wired up yet** - until one is set the sheet offers only the
copy fallback, which is deliberate (a support screen with no route out would
be worse than none) but is not the finished state. Setting the club's WhatsApp
number is a one-line config change.

**Found while checking whether the migration push had caused any of this:
`sanitize_upload` is not deployed.** The trigger added by `202609110003` went
live on production this morning and POSTs every avatar and post-photo write to
an Edge Function that only three of four exist - the deploy workflow is
`workflow_dispatch` only and was never run for it. Harmless in itself
(`net.http_post` is fire-and-forget, so the 404 costs nothing), but the
server-side EXIF/GPS stripping and magic-byte content-type check that
migration exists to provide are not actually running, while the repository
reads as though they are. Not deployed under this pass: the function *deletes*
uploads it judges non-image, which makes deploying it a destructive-capable
change that should be a deliberate decision rather than a footnote to a bug
fix. Checked and worth recording for whoever does it: iPhone HEIC is not a
hazard here, because `src/image.js` re-encodes every upload through a canvas
to WebP or JPEG before it leaves the device.

Verified: full suite 1658/1658, browser-check 43/44 in a shared-CPU run and 44/44 with the one failure re-run isolated (community-render-cost.mjs's 16 ms frame-budget trip-wire read 17.1 ms while the node suite was running on the same machine, and passes standalone - the exact contention artefact that check's own docs warn about, verified rather than assumed), version/vendor/
migration-immutability checks OK. `test/app-innerhtml-sinks.test.mjs`'s sink
pin moved 37 -> 38 for the support sheet, with the escaping audit written into
the test rather than assumed.

---

## Records hygiene: close the Advisor's last open object, and stop the docs lying about what is left — 2026-09-15

No feature work and no bug fixes. This pass went after a different class of
problem: the project's own records had drifted far enough from the code that
reading them would send someone to do work that was already done, or leave
them believing a shipped module had not been started.

**The phase board was reporting half a shipped module as not started.**
`docs/community/backlog.md` read 38 `todo`, 29 `review`, 7 `partial`, 86
`done` - while the features those `todo` rows name (the composer, the ranked
feed, reactions, two-level comment threads, the moderation queue, the
notification centre) have been live for weeks and were exercised by hand, in
a real browser and against real Postgres, by the twenty-round hunt that
closed on 2026-09-12. Reconciled against the code rather than asserted:
every non-`done` row was checked for its ticket ID cited in implementation or
a migration AND cited in a test, and 67 rows carrying both were flipped. Six
rows cited no ticket ID anywhere and were resolved by looking at the feature
instead of trusting the ID convention - COMM-106 and COMM-104 are
`renderAchievementPostCard()` / `renderWorkoutPostCard()`, both registered in
cloud.js's post-type dispatch table, and COMM-338's two halves are
`supabase test db` in test.yml's `migration-check` job plus
`scripts/smoke-test-multi-role.mjs`. The board now reads 153 `done`, 6
`partial`, 1 `todo`, and the method is written into the file so the flip can
be audited rather than taken on faith. The seven rows deliberately NOT
flipped are named individually with the reason - COMM-337 (real clickjacking
headers need the site off GitHub Pages; mitigated by `frame-guard.js`, not
closed), COMM-329 (~40 one-off `.field-label` sub-headers are still plain
divs), COMM-143 (parked with the attendance decision), and COMM-351/353/354/
368 (cross-repo, genuinely unverifiable from this workspace, so not claimed
either way).

**Two audit rows had been chasing already-closed items for a week.** VAULT-1
was resolved on 2026-09-08 by an observed 200 - `net._http_response` ids 14
and 15 at 10:20:44 and 10:21:09 UTC, the whole chain seen rather than
inferred - and `REMEDIATION_STATUS.md` recorded it correctly. But
`GO_LIVE_GUIDE.md` §A.4 and `LAUNCH_CHECKLIST.md` row 19 both still read NOT
VERIFIED, and the guide additionally still asserted the service-role key was
*invalid*. Both corrected, and that last claim explicitly retracted: the key
works, and per `purge_abandoned_profiles/index.ts:122` a 401 from that path
would not have proven the gateway rejected the token anyway, because the
function timing-safe-compares the Authorization header against the
service-role key itself. The section was rewritten rather than deleted -
the three closure attempts that each looked like proof and were not
(name-presence, `scheduled_job_health()`, a 404 on a non-existent slug) are
kept, because the same traps apply to any Vault-gated job added later. The
checklist score moves 15 PASS / 7 NOT VERIFIED to 16 PASS / 6 NOT VERIFIED,
which is a correction to the record, not new verification.

Same for `challengeKeyExists()` being "device-relative for unpublished custom
WODs, still open, unowned" in three documents: it was closed on 2026-09-07 by
`fbf5a43`, one day *before* two of those three documents repeated it as open.
The picker is a `<select>` built from `challengeKeyChoices()`, which skips
`category === "Custom"` for movements and WODs alike, and
`setWeeklyChallenge()` re-checks the same list so the DOM cannot be edited
around it. `test/community-weekly-challenge.test.mjs` already asserted
exactly this. A coordination artifact - the bullet was filed while cloud.js
was locked to another session's edit and the fix landed in that same file the
same day - not an open gap.

**The Security Advisor finding is now actually closed, not half-closed.**
`202609080005` did the expand phase in September: it rebuilt
`public.community_streaks` as a SECURITY DEFINER *function* (the shape
`feed_leaderboard`, `chal_progress`, `coach_celebrate_feed` and
`member_of_week_candidate_set` already use, which the Advisor's rule does not
flag) and deliberately left the view in place, so a client behind a
service-worker cache kept resolving its already-shipped
`.from("community_streaks")` call instead of 404ing mid-deploy. The finding
is on the view, so it stayed open the whole time the view existed.
`202609150001` completes the contract, on three verified conditions rather
than assumed ones: cloud.js has no `.from("community_streaks")` call left at
all (the one read is `.rpc`, cloud.js:1892), nothing else in the database
selects from the view (no view, function, trigger or Edge Function -
checked), and the expand phase shipped a week and twenty-three version
releases ago. A straggler client old enough to still call the view now gets
a 404 on that one request and degrades to an empty streak strip, which is
what that surface already renders for a member with no pings.

Worth stating plainly, because it is the reason this took two migrations
instead of a one-line settings change: flipping the view to
`security_invoker = true` - the obvious fix, and the one the Advisor's
wording nudges toward - would have been a silent data bug, not a fix.
`activity_pings`' only policy is `user_id = auth.uid()`, and a streak is by
definition an aggregate across every member's rows, so invoker semantics
would have zeroed every member's streak except the caller's own, on a surface
where 0 is a legitimate value and the breakage would not have looked like
breakage.

The pgTAP coverage was ported rather than dropped. `0068` was written
entirely against the view; every one of its reads is now a function call, and
its "the view is not security_invoker" check became two checks that matter
more after the contract - that the view is gone (a re-created view is a
reopened finding) and that its replacement is still definer. It was kept
rather than deleted because two of its cases, `in_leaderboards` off on its
own and `visible_to_club` off on its own, exist nowhere else: `0093` only
tests all three toggles off together, and "the combination refuses" does not
prove "each column refuses independently". `0093`'s own expand-phase
assertion ("the view still exists - do not drop it in the same migration that
adds the function") was inverted rather than removed, for the same reason.
`0064` and `0067`'s reads were converted too.

Verified: full suite 1646/1646, `supabase test db` Files=110 Tests=3429 PASS
against a fresh `db reset` over all 148 migrations, full browser-check 44/44,
version/vendor/migration-immutability checks all OK. The three hunt protocols
that produced the twenty-round review (`LIVE_BUG_HUNT_PROTOCOL.md`,
`LIVE_SECURITY_HUNT_PROTOCOL.md`, `ULTIMATE_CHECK_PROTOCOL.md`) were sitting
untracked in the working tree and are committed here, so the next pass can
re-run them instead of reconstructing them.

---

## Security hunt, round 10 (final): full-application penetration-style sweep — 2026-09-12

Three more independent agents for the closing round: admin/moderation-surface
coverage, business-logic abuse through chaining otherwise-legitimate calls, and
an unconstrained fresh-eyes sweep across the whole app with no fixed target.

**Admin/moderation surfaces: one confirmed medium-severity confidentiality
leak, fixed.** Row level security decides which rows a query can see, never
which columns - two moderation tables' "read your own row" policies were
written before staff-internal columns existed on those tables, and were never
revisited when those columns were added later. Confirmed live against real
local Postgres: a member reading their own filed report, or their own posting
restriction, could also read exactly which staff member acted on it and that
staff member's private internal notes - real deanonymization of an individual
coach or admin to the person they took action against, a staff-safety risk
distinct from anything about club-wide data. One of the two tables has no
legitimate client use for a member reading their own row at all, so that
self-read path is removed outright; the other has a real, already-shipped use,
so it is replaced with a server-side function returning exactly the safe
column set the client already asked for - the same shape this schema already
uses elsewhere to strip a real login email down to its safe portion before a
query can ever see the rest. Every privilege-escalation and moderation-bypass
path re-checked this round - role assignment, restriction lifting, pin
management, club settings, analytics access - held.

**Business-logic chaining: three confirmed gaps, all fixed.** A challenge's
own lifecycle status was never checked by its progress log - only the
participant's status was - so archiving a challenge (an ordinary settings
update, not a dedicated action) never froze it: progress could still be
logged, participants could still flip to completed, and cooperative
milestones kept auto-posting real completion announcements for a challenge
already closed out. Fixed by requiring the parent challenge to still be
active, matching the same requirement already enforced at join time.
Separately, a coach-congratulation anti-duplication safeguard from an earlier
round keyed itself on an achievement-kind label that was never case- or
whitespace-normalized, so three different spellings of the same real event
produced three real duplicate congratulations - normalized and restricted to
the fixed vocabulary the app actually uses, closing the gap the same way this
schema closes every other closed-vocabulary field. Finally, the shared
write-idempotency mechanism a prior audit added for several sensitive actions
keyed its replay-protection purely on a caller-supplied key, never on what
the call was actually about - reusing a key across two logically different
requests silently returned the first request's cached success for a second
request that never ran, with no way for the caller to tell. Closed with an
optional fingerprint bound to each call's real target, backward compatible by
construction and enabled for the two actions most exposed to this exact
failure mode.

**The unconstrained fresh-eyes sweep found nothing new.** A genuine end-to-end
pass across the remaining ordinary-member surface - the composer, profile
bio, backup import/export, search, coach-dashboard gating, upload handling,
and deep links - independently re-confirmed several earlier rounds' fixes
still hold and surfaced no new vulnerability, consistent with a tenth round
against an app that has now had nine prior rounds of focused attention.

Verified: full suite 1645/1645, full browser-check 44/44, `supabase test db`
3429/3429 against real local Postgres.

---

### Ten-round summary: the live security hunt, closed out

Stated honestly, round by round, rather than rounded up: rounds 1 and 3 found
no exploitable vulnerability at all (one Low-severity info-exposure fix in
round 1, a defense-in-depth-only tightening in round 3, and two auth-timing
observations in round 3 that trace to the underlying auth service and a
previously-accepted product decision, not to this app's own code - recorded,
not patched). Every other round - 2, 4, 5, 6, 7, 8, 9, and 10 - confirmed and
fixed at least one real vulnerability. By severity, across every confirmed
and fixed finding in rounds 1 through 10:

- **Critical**: 1 - an RLS self-referential-subquery bug letting a member
  active in one challenge forge progress into any other challenge, auto-
  posting fake public completion cards (round 7).
- **High**: 4 - PR/achievement forgery via direct table writes bypassing both
  sharing RPCs (round 4); a client-side-security-theater gap letting a
  forged achievement claim reach a public, permanent post (round 6); a
  staff-impersonation guard that never ran on a brand-new member's first
  profile write, or on the bio field at all (round 8); a database default-
  privilege gap granting TRUNCATE on dozens of tables, RBAC and audit tables
  included, to any logged-in member (round 9).
- **Medium**: the largest bucket - coach-congratulate replay and two file-
  upload gaps (round 2); moderation-notification content surviving a
  removal (round 4); an outbox identity-binding gap (round 5); three count-
  then-act race conditions in event/WOD/push-subscription capacity caps
  (round 7); a live-confirmed clickjacking chain and a missing confirm step
  on one delete action (round 8); an unpinned CI action on the production
  deploy path (round 9); a challenge-lifecycle gap, a congratulation-kind
  normalization gap, an idempotency-fingerprint gap, and a moderation
  column-exposure leak (round 10).
- **Low**: robustness gaps that raised raw errors or exposed non-sensitive
  detail instead of failing cleanly, with no schema/data exposure (rounds 1,
  4, 7, 9).

**Verification layer, honestly stated per finding class**: every
authorization/RLS/grant/database-configuration finding in this hunt was
reproduced and re-verified against real local Postgres (`supabase test db`,
direct `psql`/`docker exec`, or real two-connection concurrency tests for the
race conditions) - never against the mock, which is a hand-written JS
approximation with no real RLS enforcement behind it. Client-side/rendering
findings (clickjacking, the missing delete-confirm, notification-content
escaping) were verified live in Chromium against the mock cloud, which is the
correct layer for a UI-only property. Nothing in this hunt was reported as
confirmed on code-reading alone.

**Closing statement.** Combined with the ten-round live bug hunt that
preceded it, this application has now had twenty independent rounds of
hands-on adversarial review, sixty agents total, against its real rendered UI
and its real backend. The vulnerabilities found were real and are now fixed,
not hypothetical - every one was reproduced, not inferred, before being
called confirmed. The security posture that remains is not "no bugs will ever
be found again" - the fresh-eyes rounds (round 10's third agent here, and the
bug hunt's own final round) both still found real, fixable things others
missed, which is itself the argument for periodic re-review rather than
treating any one pass as final. What has changed is that every layer this
hunt actually tested - RLS coverage and default privileges, RPC input
handling, race conditions in shared counters, moderation/admin authorization,
client-side rendering, and the CI/deploy pipeline - was tested for real, not
assumed, and every gap found in that testing is closed with a regression test
that fails against the old code and passes against the new.

## Security hunt, round 9: infrastructure-adjacent configuration review — 2026-09-12

Three more independent agents: CSP/hosting/service-worker/manifest configuration,
Supabase project configuration (RLS coverage, grants, scheduled jobs), and
dependency/secrets/build configuration.

**Supabase project configuration: one confirmed high-severity gap, fixed.** An
earlier hardening pass closed a real anon read hole by revoking the database's
default auto-grant to every newly created table - but named only the four
read/write privilege types (select/insert/update/delete), not the other three a
table also gets by default (truncate/references/trigger, plus a fourth added in
this Postgres version). None of those three are covered by row-level security at
all - RLS only ever applies to the four DML operations - so every table created
after that hardening pass silently kept a standing grant letting any logged-in
member, and in a few cases even a fully anonymous connection, run `TRUNCATE` on
it directly, with no policy able to stop it. Confirmed live against real local
Postgres: this reached 42 of 61 tables for a plain member, including the entire
role/permission model and the admin audit log. Not reachable through the app's
own client library today (there is no path from a normal Supabase client call to
a raw `TRUNCATE`), but a real, reproducible privilege sitting underneath
everything else this hunt has verified, and exactly the class of gap that no
policy-level test could ever catch, since it lives at the grant layer instead of
in any RLS policy. Fixed by naming the remaining privilege types explicitly, the
same way the original hardening pass intended, plus closing the identical latent
gap for a future sequence (none exist in this schema today). A second,
independent default-grant entry tied to a different, more-privileged database
role was found dormant but could not be closed from a migration - a different
role's default privileges can only be changed by that role or a superuser, and
migrations run as neither for it - recorded for whoever holds direct project
access rather than silently left for the next person to rediscover. Every other
area checked (RLS actually enabled on all 61 tables, every function's search_path
pinned, scheduled-job SQL, storage bucket policy, Realtime's exposed tables) came
back clean.

**CSP/hosting configuration: one confirmed low-severity supply-chain gap, fixed.**
An earlier hardening pass pinned every CI action to an exact commit SHA except
one, which was fixed on the job that runs the test suite against a throwaway
local database - the identical unpinned pattern was still live on the job that
deploys straight to production Edge Functions with a real, privileged access
token, the higher-stakes of the two. Fixed the same way its sibling job already
was, plus a new regression test that checks every action in every CI workflow
file for a pinned SHA, so a future workflow can't reintroduce the same gap
unnoticed the way this one did. Everything else in this area - every CSP
directive against what the app actually uses, the PWA manifest, the service
worker's fetch/cache/activate logic, GitHub Actions trigger safety - was
live-tested and came back clean.

**Dependency/secrets/build configuration found nothing to fix.** No credential
of any kind (a service-role key, a real database password, a third-party API
key) exists anywhere in the repository or its full git history; every dependency
is appropriately scoped for what it does; the vendored Supabase client's
integrity check is a real, working tamper detector, independently re-verified;
every migration's seed data uses the established safe fixture pattern with no
real person's data anywhere; and no CI workflow can reach production
automatically without a human-gated, secret-protected step.

Verified: full suite 1645/1645, full browser-check 44/44, `supabase test db`
3400/3400 against real local Postgres.

## Security hunt, round 8: social-engineering-adjacent and UI-redressing — 2026-09-12

Three more independent agents: clickjacking/UI-redressing, display/identity spoofing,
and notification/invite/deep-link social engineering.

**Clickjacking: the host's own known, already-documented limitation, upgraded from
theoretical to a live-confirmed exploit chain, and given the one mitigation actually
available.** This repo has long and accurately documented that `frame-ancestors` in a
`<meta>` CSP is spec-ignored, and that the static host this app ships from has no way
to send a real HTTP response header — an accepted, low-severity, "nothing to do about
it here" finding. Confirmed live this round that the gap is exploitable, not just
theoretical: an invisible iframe positioned over pre-measured real coordinates, behind
an ordinary-looking decoy page, silently executed a real destructive action ("leave
challenge") on a signed-in member who never saw the app's own confirmation text - the
same technique reaches every destructive confirm action in the app. Real HTTP headers
still cannot be sent on this host, but a client-side check can run regardless: a
legitimate load (an installed PWA, an ordinary browser tab) always has its own window
as its top window, so a same-origin check that hides the page whenever that is not
true costs nothing for a real user and closes the gap a header-only mitigation cannot
reach on this host. (Also confirmed live: modern Chromium additionally blocks a framed
page from navigating itself out to safety without a prior user gesture - the hide-on-
detection half of the fix is what actually stops the attack; the navigate-away half is
kept as a harmless best-effort addition, not the load-bearing part.)

**Display/identity spoofing: one confirmed high-severity gap in an existing guard,
fixed.** An earlier round's free-text staff-impersonation guard (blocking a plain
member from setting a display name like "מאמן דני") only ever ran on an UPDATE to an
existing row - and a brand-new member's very first profile write is an INSERT, since
there is no prior row to update. A new member could set a staff-claiming name on day
one and simply never edit it again, keeping an unenforced impersonation permanently;
confirmed live against real local Postgres. The same free-text claim also worked
un-guarded in the bio field, insert or update, which the original guard never covered
at all. Fixed by extending the same check to run on insert as well as update, across
both fields, with the same staff-word list and the same exemption for members who
actually hold the role they're claiming.

**UI-redressing: one confirmed medium-severity gap, fixed - an in-app control, not a
framing attack.** Every destructive delete action in the offline training log routes
through an explicit confirmation step, except one: deleting a custom WOD definition
deleted it immediately on a single tap, with its small delete control sitting flush
against the primary "select this WOD" button beside it in the picker list, with no
visual gap between them. Fixed with the same confirmation pattern every sibling delete
action already uses, and a real gap between the two controls so they no longer read as
one continuous tap target.

**Notification/invite/deep-link social engineering found nothing to fix.** A
crafted deep-link parameter only ever opens a view, never auto-executes an action; a
notification's title is always a fixed, honest, client-side label per type, never
overridable by free-text content even though a comment's raw body is echoed into its
own notification; an invite code's role is independently capped server-side regardless
of who is sending it; and there is no feature at all that shows a new member who
"invited" them, so there is nothing there to spoof. Confirmed live against both the
mock and, for every authorization-layer question, real local Postgres.

Verified: full suite 1641/1641 (new regression coverage for the confirmation step and
the impersonation-guard's insert/bio coverage), full browser-check 44/44 (new
frame-guard.mjs scenario proving a framed load is hidden and un-hit-testable while an
ordinary load is untouched), `supabase test db` 3393/3393 against real local Postgres.

## The square-glow bug, reported twice, actually fixed this time — 2026-09-12

Real device screenshot: an earned bronze plate medal's glow looked like a square, not
a circle. This exact bug was reported once before and "fixed" by splitting the plate's
circular clip (`.medal-plate`) and its glow filter (`.medal-shape-plate`) onto two
separate, nested elements, on the theory that `filter:drop-shadow()` on an ancestor
doesn't reliably respect a descendant's `overflow:hidden` clip. It didn't work - this
device report is the proof - because the theory was incomplete: drop-shadow traces the
alpha of an element's entire rendered subtree regardless of which specific descendant
does the clipping, so moving the clip to a child changes nothing about a browser whose
drop-shadow implementation falls back to the pre-clip layout box for that whole
subtree. Confirmed this repo's own Chromium checks never would have caught it either
way - the isolated CSS renders a clean circle there, so this is real, browser-specific
render behavior, not something reproducible in this sandbox by design.

The actual fix removes the ambiguity instead of trying to work around it: an earned
plate's glow is no longer `filter:drop-shadow()` on an ancestor at all - it's a real
`box-shadow` applied directly to `.medal-plate`, the element that actually carries
`border-radius:50%`. `box-shadow`'s shape is defined by spec to follow its own
element's border radius; there is no filter-compositing step and therefore no
ambiguity for any engine to get wrong. The shield/circle SVG shapes (milestone/rx/
capstone medals) keep drop-shadow, unaffected - a real SVG vector path is exactly what
drop-shadow traces correctly everywhere, so the fragility is specific to an HTML div
clipped by CSS, which only the plate shape uses.

`test/medals.test.mjs`'s own header comment (which recorded the first, incomplete
fix as settled) is corrected to say so plainly, and a new test asserts the CSS
mechanism directly - the earned rule must be a `box-shadow` on `.medal-plate`, and
`filter:drop-shadow` must never again apply unconditionally to every `.medal-shape` -
so a future edit can't quietly reintroduce this without a test noticing before a
third device report.

Verified: `test/medals.test.mjs` (6/6, one new), `brass-contrast.test.mjs`/
`theme-token-parity.test.mjs` (shared CSS file, unaffected), full suite green, and a
direct visual check (real Chromium) confirming no regression in the glow's own
appearance - the actual cross-engine claim rests on the CSS mechanism being provably
unambiguous by spec, not on a screenshot this sandbox's one browser engine can produce
either way.

## Security hunt, round 7: API/RPC contract abuse — 2026-09-12

Three more independent agents: malformed or unexpected-type RPC parameters, race
conditions in multi-step operations, and Supabase Edge Function security.

**Malformed RPC parameters: one confirmed critical authorization bypass, one
confirmed low-severity robustness gap, both fixed.** A policy meant to check
"is the caller an active participant of THE CHALLENGE this row is for" had a
self-referential subquery bug that silently degraded it to "is the caller an
active participant of ANY challenge at all" - trivial to satisfy, since joining
any open challenge is self-service. Confirmed live against real local Postgres:
a member active in one challenge could write fabricated progress into a
completely different, never-joined challenge, and a cooperative challenge's own
completion trigger sums that log with no participation check, so a forged
delta could push a challenge past its milestones and auto-post real,
feed-visible "100% complete" cards nobody earned. Fixed by qualifying the
policy's column reference so it actually checks the row being written, the
same way this schema's other insert-self policies already guard against a
subquery shadowing the outer column - closing the hole without narrowing the
already-shipped, already-tested behavior of a completed participant still
being allowed to log a compensating correction into their own challenge.
Separately, two RPCs that build a jsonb-sourced row cast a handful of
caller-supplied fields (a photo's position/width/height, a batch entry's
post/session id) straight into a typed column with no validation, so a
wrong-shaped value raised a raw, unhandled Postgres error instead of a clean
outcome - confirmed not to leak schema/internal detail to the client, low
severity, fixed by validating each field's shape first and falling back the
same way a missing field already did, rather than letting a bad cast throw.

**Race conditions: three confirmed count-then-act gaps, all fixed with the
locking pattern this codebase already uses correctly elsewhere for the exact
same shape.** Three separate count-then-insert caps - a capacity-limited
event's RSVP cap, a per-day structural cap on how many programmed-WOD cards
the feed can gain in one day, and a per-account cap on how many push
subscriptions one member can hold - each read a count and compared it to a
limit with no lock behind either read, so two requests arriving close together
could both read the same pre-insert count and both pass. Confirmed live
against real local Postgres with genuinely concurrent connections: all three
caps could be oversold by exactly the number of concurrent callers. Fixed with
row-level locking where a natural row exists to lock (the event being RSVP'd
to, the same pattern this codebase's own cooperative-challenge progress
trigger already uses correctly) and a transaction-scoped advisory lock keyed
to the resource being capped where no such row exists yet (the day being
programmed, the account registering a subscription) - serializing the
count-check-write section per key instead of leaving it open to two readers
racing the same stale count.

**Edge Function security found nothing to fix.** All four functions
(admin_reset_password, purge_abandoned_profiles, recap_weekly,
sanitize_upload) were live-tested against the local stack: each correctly
re-derives the caller's real privilege server-side rather than trusting a
client-asserted role, none leaks cross-user data, no secret material lives
client-side beyond the intentionally public anon key, and every credential
check held under a non-admin token, a missing auth header, and a malformed
JWT. One environment-level observation, not an app-code issue: the local
Supabase CLI's own API gateway injects a permissive CORS header regardless of
what the function itself returns - low practical impact against a
Bearer-token endpoint (no cookie for a cross-origin page to ride), and worth a
quick manual check against a real deployed instance, but nothing in this
repository to fix.

Verified: full suite 1639/1639, full browser-check 43/43, `supabase test db`
3387/3387 against real local Postgres, including a live two-connection
reproduction of all three race conditions before the fix and their absence
after.

## Security hunt, round 6: secrets/crypto handling and client-enforced-only checks — 2026-09-12

Three more independent agents: secrets and cryptographic-material handling, controls that
exist only on the client, and general authorization-boundary re-checks against real local
Postgres.

**Client-enforced-only checks: one confirmed high-severity gap, fixed.** Unlocking an
achievement through the claim RPC and sharing it to the public feed are two separate
steps. For most metrics the claim RPC has no server-side record of the underlying
count to check against - a documented, pre-existing gap the codebase already called out
in its own migration comments - so the claim step alone could not distinguish a real
unlock from one requested for a metric that never actually happened. Confirmed live
against real local Postgres: nothing on the sharing side re-checked this either, so a
fabricated claim flowed straight through to a public, feed-ranked achievement post
carrying full social proof, indistinguishable from a real one. Fixed at the layer
that was actually missing a boundary, not by trying to reconstruct every metric
server-side (the offline training log a member's own device syncs has no structural
validation on its contents and can't safely be trusted as a verification source without
much larger work, so that path was deliberately not used): a new column records,
authoritatively and only at insert time, whether an achievement's own definition is one
of the kinds the server can currently verify: those unlocks are marked verified and may
still be shared, while any not currently server-checkable are marked unverified and the
sharing step now refuses them outright. Nothing about a legitimate member's real
unlocks changes; the earlier-flagged gap in claim-time verification for the
not-yet-checkable metrics remains open and tracked, but can no longer turn into a
public, permanent post.

**Secrets/crypto handling and the rest of the authorization re-check found nothing to
fix** - no secret material lives client-side beyond the intentionally public anon key,
every credential-bearing table stays behind RLS scoped to its own owner, and the
authorization boundaries re-walked this round all held.

Verified: full suite 1639/1639 (new regression coverage for the verified-flag trigger
and the share-time gate), full browser-check 43/43, `supabase test db` 3369/3369 against
real local Postgres, including a direct-insert test proving the trigger is authoritative
even when a caller bypasses the claim RPC entirely.

## Live bug hunt, round 10 (final): cross-feature interaction and the full-app sweep — 2026-09-11

The tenth and final round of the live bug hunt: feature-interaction
combinations, a throttled-network walkthrough, and a final fresh-eyes
sweep by an agent given no target beyond "use the app for real, end to
end." Six confirmed bugs, the most of any single round.

**High: 40 of the app's 59 achievement badges rendered as flat, colorless
circles/shields with no glyph.** Every non-PR-tier medal (milestone/Rx/
capstone) is drawn as `<use href="#medalCircle"/>` referencing a shared
`<symbol>`, styled by CSS rules written as descendant selectors
(`.tier-bronze .medal-rim{...}`) reaching from the outer wrapper down into
the referenced content. This Chromium build does not match a descendant
combinator across a `<use>` reference, so every one of those rules silently
applied to nothing - only the PR/streak tiers were unaffected, because
they were already migrated to plain PNG plate images. Fixed by moving
every rule to a plain (non-descendant) selector fed by a CSS custom
property inherited from the tier/type class - `currentColor` and custom
properties DO reliably cross a `<use>` boundary even though descendant
selectors don't, which is the standard fix for this exact class of SVG
bug. Verified with a real pixel-sampled screenshot
(`scripts/browser-check/medal-icon-colors.mjs`), since `<use>`-referenced
content has no DOM a script can query directly.

**Data loss: an achievement crossed while offline was marked claimed
locally before the server had actually received it, and never retried.**
`syncCommunityMilestones()` (app.js) persisted a freshly-crossed code as
claimed and fired the claim RPC without awaiting it; a genuine network
failure surfaced as an uncaught "Failed to fetch" rather than a clean
failure the caller could see, and the code was never retried once
connectivity returned - the real Community-side achievement record was
permanently lost. Fixed by only marking a code claimed once the RPC
confirms it actually ran (a network exception or a server error now both
leave the code eligible for the next sync), matching every other
offline-safe write path in this app.

**Medium: the challenge list-card "Join" button had no busy guard, so a
double-tap on a slow connection showed a false failure toast after a
genuine success.** Only the open detail dialog's own button was guarded;
the list card's could fire `joinChallenge()` twice, and the real
`(challenge_id, user_id)` primary key let the second insert lose an
honest 23505 race - overwriting "הצטרפת לאתגר" with "לא ניתן היה להצטרף"
even though the member had joined. Fixed with a per-challenge busy guard
shared by both buttons (matching `reactionBusy`/`followBusy` elsewhere in
this file) and by treating a losing duplicate-key race as success, not
failure - the member IS a participant either way. The same missing-guard
shape on the feed's quick-action event-RSVP buttons was fixed too, though
it had no visible symptom (`event_rsvp` is a real upsert).

**Medium: a stalled anonymous sign-in could hang the Community tab forever
with zero controls.** `ensureAnonymousSession()` awaited
`signInAnonymously()` with no timeout; a connection that neither resolved
nor rejected left "מתחברים לקהילה…" on screen indefinitely, with no retry,
no cancel, and no recovery even from leaving and re-entering the tab for
the rest of the session. A 15-second client-side timeout now gives a
stall the same outcome an explicit sign-in error already had.

**Medium: date labels never showed the year, making same-day-of-month
entries from different years indistinguishable.** `fmtDate()` formatted
every date as day/month only; a progress chart plotting a real 1RM gain
three years apart showed two identical "11.03" x-axis points, with the
same ambiguity in History rows and delete-confirmation dialogs. Fixed to
append the year, but only when it differs from the current one, so the
common (this-year) case is unchanged and no more cluttered than before.

**Incidental, found while verifying the fixes above:** four test files
computed "today" the same UTC way `todayIso()` used to (before round 6's
fix) - once that fix correctly made the app's own "today" local, these
fixtures started disagreeing with it for the same 2-3-hour nightly window
the original bug was about, confirmed for real when this exact suite ran
right through that window. Updated to match the app's own local-date
convention.

**Checked and found clean:** editing/deleting an unrelated entry while a
celebration overlay is open (genuinely blocks all clicks underneath, no
click-through); forcing Settings open on top of a celebration (closes the
topmost dialog first, no trap); the WOD builder opened over an active
undo toast; a deferred celebration flushing mid-edit of an unrelated,
unsaved entry (all state survives); switching tabs mid-ladder and
mid-superset across multiple detours (group state survives every
scenario); every other busy-guarded action under a throttled connection
(post publish, comments, reactions, invite redemption, report submission,
feed/directory/invite-list pagination, challenge/event detail dialogs
remaining closeable while loading); and, across both a zero-data and a
multi-year fresh-eyes walkthrough, no console errors and no other
confirmed defect beyond the two above.

Verified: full suite 1639/1639 (9 new/updated regression tests across
`test/live-bug-hunt-round10.test.mjs`,
`test/community-achievement-engine.test.mjs`,
`test/community-challenges.test.mjs`, `test/community-gate-order.test.mjs`,
plus the four test-fixture date fixes), full browser-check 43/43 (new:
`medal-icon-colors.mjs`, verified with real pixel sampling and a control).

## Live bug hunt, ten-round summary — 2026-09-11

Ten rounds, 30 fresh agents (3 per round, no memory of prior rounds),
against this app's own real rendered UI in Chromium, mocked backend only,
production Supabase never touched. Confirmed bugs by round, all fixed with
a paired regression test (a node-level test for state/logic, a real-browser
`scripts/browser-check/*.mjs` script with a control for anything CSS/
rendering/geometry jsdom cannot see):

- **Rounds 1-5** (already run and documented before this continuation):
  15+ bugs across core training log, achievements/notifications/back-button,
  Community member/admin surfaces, offline-sync/PWA lifecycle,
  settings/a11y/keyboard nav, and Club WOD board/invites.
- **Round 6** (Hebrew grammar/RTL, extreme content values, units/dates/
  locale): cloud.js computed "today" from UTC instead of local time; a
  multi-line session note silently lost its line breaks; an RTL-override
  character spoofed a display name's rendered identity; nine Hebrew
  singular/plural grammar bugs; raw ISO dates in admin UI; a DST drift in
  one tenure-badge calculation; a long-name layout overflow.
- **Round 7** (cross-tab/multi-window/concurrent-session): a severe, silent,
  permanent IndexedDB cross-tab schema-upgrade deadlock; a
  QuotaExceededError leaving the UI celebrating a save that never
  persisted; bodyweight/measurement saves creating duplicate rows across
  two tabs; a minor invite-redemption gate regression on reload.
- **Round 8** (analytics/dashboards/numeric accuracy): the admin analytics
  dashboard showing stale data under a just-switched period's own header;
  the onboarding "first month" card silently dropping a mid-week joiner's
  entire join-week activity; a legacy leaderboard ignoring the
  `in_leaderboards` opt-out and lacking a deterministic tie-break, closed
  with a real schema migration verified against local Postgres.
- **Round 9** (long-term data lifecycle): ordinary app boot silently
  discarding real data past 20,000 rows per store (an import-only cap
  applied everywhere); "delete all data" leaving real records behind in
  two write queues, with a real cloud-resurrection risk; session notes
  excluded from every backup and wiped unrecoverably by delete-all; a
  returning long-time member shown the fresh-install welcome sheet.
- **Round 10** (feature interactions, throttled network, final sweep): 40 of
  59 achievement badges rendering colorless (a `<use>`/CSS-descendant-
  selector bug); an offline achievement claim silently and permanently
  lost; a challenge-join race producing a false failure toast after a real
  success; an anonymous sign-in that could hang forever with zero
  controls; date labels never showing the year.

**Lightly covered, worth a future pass:** Realtime (`postgres_changes`)
behavior end-to-end (no local Realtime container was available in any
round that touched it); the coach dashboard's Engage/decline-detection
surfaces (explicitly scaffolded and deferred pending attendance data,
per the coach-tools agent's own scope); push notification delivery on a
real device (only the in-app center and preference plumbing were
exercised); and the very largest data volumes (round 9 tested a confirmed
20,000-row cap fix at a representative 50-row scale for suite speed, with
the full 21,000-row live reproduction done once, in the browser, by the
reporting agent rather than in the committed regression suite).

## Live bug hunt, round 9: long-term data lifecycle — 2026-09-11

Three fresh agents: multi-year training-log performance/correctness, data
completeness on export/delete-all, and multi-version upgrade paths - all
about what happens to a real member's data over years of real use, not a
single session.

**Severe: ordinary app boot silently discarded real data past 20,000 rows
in any one store.** `sanitizeList()`'s `max` parameter always defaulted to
`LIMITS.importItems` (20000) - a limit designed to bound an untrusted JSON
backup file - but the function is also called by `reloadFromDb()` on
*every normal boot*, for every store. Confirmed live: 21,001 seeded
strength entries all persisted correctly to IndexedDB, but only 20,000 were
ever visible to the running app after a reload, with no error or warning.
Because IndexedDB's `getAll()` orders by primary key (a random id, not a
timestamp), the ~1,000 dropped rows were scattered roughly uniformly across
the whole dataset - not a clean "drop the oldest" trim, and not
recency-safe: any given row, including a recent PR, was as likely to be
dropped as any other once the count crossed the threshold. A years-active
member logging multiple sets a session is a realistic way to reach it.
Fixed by making the cap an explicit opt-in parameter, passed only at the
one JSON-import call site it was actually meant for.

**Severe: "מחיקת כל הנתונים" left real data behind in two write queues.**
Neither the private-records sync outbox nor the Community write outbox was
ever cleared by delete-all - confirmed live, full record payloads (weight,
reps, movement names, WOD text) survived a real delete-all in both stores.
Every save in `src/db.js` unconditionally queues a row to the first store
regardless of whether cloud backup is even on, so it fills up for every
member; a working `HaimuniaOutbox.clearAll()` already existed for the
second store but had zero call sites anywhere in the codebase. Beyond the
immediate "delete didn't actually delete" problem, a member who enables
backup after running delete-all risked the leftover rows syncing to the
cloud and resurrecting data they had just deleted locally. Fixed by adding
the missing bulk-clear for the first store and wiring the existing one in
for the second, both now called from `clearAllData()`.

**Medium: session notes were never in a backup, and delete-all wiped them
unrecoverably.** `buildBackupPayload()` covered the seven record groups but
never the free-text session notes stored per calendar day - including in
the auto-downloaded safety backup `clearAllData()` takes right before
wiping everything. The Settings screen's own copy frames export as "the
full training log"; a member's actual reflections on a session are
training-log content by that reading, unlike the name/box-start-date
exclusion (which is explicitly disclosed in that same copy and is correct
as-is). Now included in every export and restored on import. The same fix
also picked up a small, low-severity sibling gap: WOD-builder movement
suggestions (`wodMovementTags`) were exported nowhere though cleared on
delete - the underlying movement names were never actually lost (they live
inside each custom WOD's own description), only the autocomplete cache.

**Confusing for skip-upgraded users: a returning member with years of real
history but no stored name got the fresh-install welcome sheet.** Every
other first-run flag bootstrapped at boot correctly grandfathers a device
with real data (`isFreshInstall`), but the welcome-sheet trigger checked
only `userName === null` - a device that predates the naming step got the
"ברוכים הבאים לאימוניה" sheet on top of years of its own training history,
and because of the `if`/`else if` shape, the release-notes catch-up was
silently skipped for that same boot too. Fixed to match every sibling
flag's own grandfathering rule; a grandfathered member can still set a name
any time via Settings' edit icon, unchanged.

**Checked and found clean, at real scale:** chart rendering at ~1,095-1,831
points over a ~6-year range (no hang, correct horizontal scroll); calendar
navigation across 39 consecutive month clicks and real Dec→Jan/leap-year
boundaries; PR/rep-record correctness under a same-day, identical-timestamp
5-way tie; a full 5,116-row multi-year dataset loading with an exact
in-memory/on-disk count match; every other exported/deleted record type
(entries, WOD entries including EMOM fields, custom movements/WODs,
bodyweight, measure types and values); the legacy `userName`
localStorage→IndexedDB migration; a genuine v1-era (single-store) and
v2-era IndexedDB shape both upgrading cleanly straight to the current
schema with no data loss; every `localStorage` key (including two
deliberately corrupted with non-JSON garbage) defaulting safely when
absent; and the service worker's own update mechanism, which has no
sequential-version assumption to begin with.

Verified: full suite 1635/1635 (10 new/updated regression tests across
`test/live-bug-hunt-round9.test.mjs`, `test/clear-data.test.mjs`,
`test/import-export-ui.test.mjs`, `test/community-dormancy-warning.test.mjs`),
full browser-check 42/42.

## Live bug hunt, round 8: analytics, dashboards, and numeric accuracy — 2026-09-11

Three fresh agents: admin analytics dashboard accuracy, recap content
accuracy, and leaderboard/ranking accuracy. Each hand-constructed a known
dataset and verified the app's displayed numbers against a hand-computed
expected value, rather than just confirming something rendered.

**Misleading admin decision-making: switching the analytics period showed
the old period's numbers under the new period's own date header.**
`loadAdminAnalyticsDashboard()` set `a.loading = true` on every period
change but never cleared `a.data`, so the skeleton guard
(`a.loading && !a.data`) only ever fired on the very first load - every
later mode toggle or prev/next page kept the previous period's numbers on
screen, with no loading indicator, for the whole RPC round-trip, while the
period selector's own header already showed the new dates. Confirmed live:
paging week -> month displayed the old week's peak figure under a header
already reading the new month's range. Fixed by clearing `a.data` the
instant a new period load starts, so every re-fetch shows the skeleton, not
a stale number that no longer matches what's labelled above it.

**Misleading content to real members: joining mid-week silently dropped
that week's own sessions/PRs/achievements from the "first month" card.**
`weekly_recaps.week_start` is always the Monday of its ISO week (a DB
constraint); the onboarding summary queried `week_start >= redeemedAt`,
which excludes the entire join-week row whenever a member joins on any day
but Monday - most real signups. Confirmed live: a Wednesday join with 3
real sessions, a PR, and an achievement that same week rendered "0 שיאים
ו-0 הישגים" and undercounted sessions by those 3. Fixed by lower-bounding
the query at the Monday of the join week instead of the join instant
itself, matching the DB's own week_start convention.

**Unfair ranking, real DB fix: the legacy "אתגר השבוע" leaderboard ignored
the in_leaderboards opt-out and had no deterministic tie-break.** Unlike
every later ranked view (`feed_leaderboard`, `challenge_progress_view`),
`weekly_challenge_leaderboard` (202608270001) predates both the
`in_leaderboards` privacy toggle and this app's deterministic-tie-break
convention. Confirmed live: a member with `in_leaderboards=false` and the
week's highest score still rendered at rank #1 with the trophy - the same
"hide my result" toggle gave a false sense of being hidden. Separately, two
members tied on score rendered in whichever order Postgres happened to
return rows in, which flipped between two loads of identical data, and the
client's `.limit(50)` with no `.order()` meant a challenge with 51+ entrants
could rank an arbitrary subset rather than the true top 50. New migration
`202609110007_weekly_challenge_leaderboard_privacy_and_order.sql` adds the
same `can_view_profile_field(author, 'in_leaderboards')` gate every later
view already has, plus a deterministic `ORDER BY` (score by direction,
then occurred_on/display_name/post id as a stable tie-break) - sufficient to
fix both bugs without touching the client, since JS's `Array.prototype.sort`
is stable and now receives rows in a deterministic order to begin with.
Verified against real local Postgres (`supabase test db`, new pgTAP file
`0100_weekly_challenge_leaderboard_privacy_and_order_test.sql`): an
opted-out member's post never appears despite the highest score, and a
genuine tie resolves identically with or without an explicit `ORDER BY` on
the query.

**Checked and found clean:** the admin dashboard's zero-activity rendering
(honest zeros/em-dashes, no NaN), its ratio/count formatters distinguishing
real 0 from null, per-member-vs-per-club field mapping across all 18
metrics; the weekly recap dialog's quiet-week state and its DST-immune
week-range label (verified across Israel's real 2026 spring-forward
transition); the monthly club recap's zero-activity rendering; the modern
`feed_leaderboard`-backed boards (consistency streak, challenge progress)
under the identical tie/opt-out/moderation conditions that broke the legacy
board - all three came back clean, including the moderated-content exclusion
the legacy view already had right.

Verified: full suite 1629/1629 (7 new/updated regression tests across
`test/community-admin-analytics-dashboard.test.mjs`,
`test/community-onboarding.test.mjs`), full browser-check 42/42, and
`supabase test db` 3360/3360 against real local Postgres including the new
migration and its pgTAP coverage.

## Live bug hunt, round 7: cross-tab, multi-window, and concurrent-session behavior — 2026-09-11

Three fresh agents: same account in two tabs, interrupted async operations,
and storage-quota/IndexedDB edge cases. All three areas are specific to the
offline training log's IndexedDB layer (`src/db.js`), since the Community
layer's mock-backend harness turned out not to support genuine cross-tab
shared state (documented, not fixed - a harness limitation, not a product
gap).

**Severe: a cross-tab IndexedDB schema-upgrade deadlock, silent and
permanent.** `openDB()` had neither half of the standard IndexedDB
version-upgrade handshake: no `onversionchange` telling an idle connection
to step aside for a newer one opened elsewhere, and no `onblocked` on the
side requesting the upgrade. Confirmed live with two real tabs: an entirely
ordinary "left open in the background" tab A permanently blocked tab B's
open request the moment a schema version bump (this app's own `v10 adds
communityOutbox` comment shows this has already happened once) landed -
tab B sat on "טוען את היומן שלך…" forever, no error, no timeout, until tab A
was manually closed. Fixed with the standard pair: every connection now
closes itself the instant a newer version wants in, which is what stops
another tab from ever blocking for more than an instant in the first place.

**Silent data loss + permanently corrupted one-time state: a failed
IndexedDB write left the UI believing it had succeeded.** `saveSet()`/
`saveWod()` mutated in-memory state and decided the whole
celebration/PR-flagging flow *before* awaiting the actual write, with no
rollback on failure. Confirmed live with a forced `QuotaExceededError`: the
full-screen "first log arrival" celebration fired, a PR flag got set, and
`firstLogCelebrated` was permanently stamped `true` in a *different*
(unaffected) store - all while the entry silently never persisted, so a
reload showed it simply gone and the one genuinely-first successful save
would never see that celebration again. Fixed by writing to IndexedDB
*first* and returning immediately (with the existing storage-error banner
shown) on failure, before any in-memory mutation happens - a failed save now
has no visible side effect at all, matching what "failed" should mean.

**Silent data corruption: two tabs each logging today's bodyweight/
measurement created two permanent, orphaned rows instead of one.**
`saveBodyweight()`/`saveMeasurement()` upserted "today's" row by scanning
each tab's own in-memory array. Confirmed live for both: tab A saves 80kg,
tab B (never reloaded, in-memory array still empty) saves 82kg for the same
date - two rows on disk, the older one silently orphaned and still feeding
the weight chart as a duplicate point. Fixed the same way an earlier round
fixed the identical class of bug for editing a strength set/WOD entry:
re-read the on-disk row for today right before deciding update-vs-insert.

**Minor: reload during invite-code redemption bounced an already-joined
member back to the start screen.** `state.signupStarted` is in-memory-only
and resets on reload; if the redemption RPC actually committed server-side
before the reload cut off the response, the member landed back on the
neutral "יש לי קוד הזמנה" screen as if signup had never begun - retyping the
same (now-spent) code then failed with a generic error. Self-recovered via
a second tap on the same entry point, but this closes it directly: a
confirmed server-side redemption is now as strong a signal as
`signupStarted` for skipping the neutral gate.

**Documented, not code-fixed:** a round-7 agent found that once the real
service worker is active, a `page.reload()` in a browser-check script can
have `vendor/supabase.js` served from the SW's own cache rather than by
`installMockCloud`'s `page.route()` stub - confirmed the mock client got
silently replaced by the real factory after such a reload, though no actual
request to production ever fired (the separate blanket `*.supabase.co`
abort held throughout). Not defaulted into `installMockCloud` because
`update-flow.mjs` deliberately exercises the real service-worker lifecycle
against the same mock and would break; documented in `lib/mockCloud.mjs`
with the `serviceWorkers: "block"` guidance for any future reload-heavy
script.

Verified: full suite 1627/1627 (9 new/updated regression tests across
`test/live-bug-hunt-round7.test.mjs` and `test/bodyweight-measurements.test.mjs`,
plus two pre-existing source-text-sweep tests updated to match the widened
gate condition), full browser-check 42/42.

## Live bug hunt, round 6: Hebrew grammar/RTL depth, extreme content values, and units/dates/locale — 2026-09-11

The 5-round hunt from earlier today was called "final" prematurely - the full
protocol runs 10 rounds. Continuing from round 6: three fresh agents on Hebrew
grammar & RTL content depth, extreme content values, and units/dates/locale
formatting, none of which the first five rounds covered.

**Highest-impact fix: `cloud.js` computed "today" from UTC, not local time.**
`todayIso()` was `new Date().toISOString().slice(0,10)` - the UTC calendar
date. Israel is always ahead of UTC, so for 2-3 hours after every local
midnight this returned yesterday's date. Confirmed live (Chromium,
`Asia/Jerusalem`, clock fixed to 01:00 local): the feed's "pinned note for
today" showed yesterday's stale pin while today's real one sat in the
archive, and the Club WOD board labeled today's own session "מחר" (tomorrow)
in one panel while app.js's own board panel simultaneously said "today" for
the same session - because app.js's own `todayISO()` (`src/format.js`)
already builds the date from local Y/M/D and was never affected. Fixed by
matching that same local-date construction; every caller (the pin write
side, the realtime today-strip filter, the weekly-challenge active window,
activity pings, achievement-share `occurred_on`) funnels through the one
function, so one fix closes the whole class. `clubWodDateLabel()`'s own
yesterday/tomorrow shift math had the identical UTC-vs-local gap one level
down and got the same local-date fix.

**Silent data loss: multi-line training notes lost their line breaks.**
`saveSessionNote()` ran the note through `cleanStr()`, which deletes
`\n`/`\r` outright - correct for the single-line fields it was built for,
wrong for the one genuinely multi-line field in the app (`sessionNoteInput`,
`rows="3"`). A real 3-line reflection was saved with its sentences silently
fused together word-to-word, no warning. `cleanMultilineStr()` is now a
named sibling in `src/shared/safe-helpers.js` for exactly this shape of
field - same control-char/bidi/zero-width stripping, minus deleting
tab/LF/CR.

**Identity spoofing via an RTL-override character.** `cloud.js`'s
`saveProfile()` sanitized `display_name`/`bio` with only
`.trim().slice(N)` - no control-char, bidi-override, or zero-width
stripping at all, despite `cleanStr()` existing and being used everywhere in
`app.js` since COMM-368. Confirmed live: a display name typed as
`"safe_photo" + U+202E + "gnp.exe"` stored and rendered as
`"safe_photoexe.png"` on every surface showing it (profile, feed author,
search) - a classic filename/identity spoof. Fixed at the shared
`cleanStr()` layer (now strips Unicode bidi format controls and zero-width
characters, not just ASCII control chars, closing the same gap for every
`cleanStr` caller in both clients at once) and wired `cleanStr` into
`cloud.js` for the first time, applied to `saveProfile`, `postAnnouncement`,
and `setWeeklyChallenge`. `nameHtml()` also now isolates a stored name
through `bidiText()` as defense-in-depth. The same stripping incidentally
closed a second, related gap: a zero-width-only display name used to store
and render as an invisible blank while still passing "has a display name"
truthy checks - it now cleans down to an actually-empty string.

**Nine Hebrew singular/plural grammar bugs, one shared root cause.** The
same missing-singular-branch pattern this repo already fixed once for the
streak label recurred at nine more sites, several on very high-traffic
surfaces: `relativeTime()` (feed/comment/mod-queue/audit-log timestamps -
"לפני 1 ימים" instead of "לפני יום"), the moderation queue's reporter count
and the Manage-tab pending-reports banner, the reaction-count strip,
event/challenge participant counts (four sites, now one shared
`participantsLabel()` helper), the coach "new members" row's day/session
counts, the consistency-challenge weeks label, the onboarding first-month
recap card (whose own test had literally asserted the wrong grammar as
correct), and the backup-import confirm dialog. All fixed with the same
explicit-singular-branch shape the existing streak-label fix already used.

**Cosmetic, systemic: raw ISO date fragments in admin/coach UI.** Invite
lists, member/ghost rows, the directory profile sheet, and achievement/event
"when" labels printed `2026-06-15` directly into otherwise-Hebrew-formatted
text. Added `shortHebDate()` (compact D.M.YYYY) and applied it to the
read-only display sites - never to anything feeding a form or
`<input type="date">` value, which still needs the raw ISO string.

**Minor DST fix:** `daysSinceBoxStart()` did raw millisecond division,
which drifts by the DST offset right at a transition and can flip a
tenure/anniversary badge's day count off by one for about an hour. Now
counts local calendar days the same way `computeCurrentStreak()` already
does elsewhere in this file.

**Layout fix:** an 80-character unbreakable name (`cleanStr`'s own cap)
overflowed `.who-name` on the Settings screen and bled under the adjacent
edit-icon button. Added `overflow-wrap:anywhere`, verified with a real
Chromium measurement plus a control proving the same page would overflow
without it (`scripts/browser-check/who-name-overflow.mjs`).

**Checked and found clean:** number formatting inside RTL text (already
correctly isolated via `bidiText`/`bidiWrapRuns`), gender agreement in every
generated sentence (the app's `/ה` suffix convention holds everywhere),
weight units (kg-only throughout, no leftover lb references), emoji-only and
mixed RTL+emoji+English display names, zalgo-style combining-diacritic
stacking (capped, contained, not a layout break), and the WOD/reaction
"and N more" labels that already special-cased singular correctly.

Verified: full suite 1620/1620 (13 new/updated regression tests across
`test/live-bug-hunt-round6.test.mjs`, `test/roadmap-features.test.mjs`,
`test/community-onboarding.test.mjs`, plus three pre-existing tests updated
to match the corrected grammar/date-format output they were asserting
against), full browser-check 42/42 (new: `who-name-overflow.mjs`).

## Security hunt, round 5: supply chain, PWA surface, and a full assume-breach pass — 2026-09-11

Three more independent agents: third-party & supply-chain review, PWA/service-worker
attack surface, and a final defense-in-depth verification pass re-testing today's own
fixes directly at the RPC boundary. This is the fifth and final round of today's hunt.

**Supply chain: no confirmed gap.** The vendored `supabase.js` integrity check
was tested, not just read - three separate byte-level tampers of a scratch copy
(a single flipped byte, an appended exfiltration payload, a subtle token edit)
were all caught by the sha256 pin, and the check runs unconditionally in CI on
every push. External CDN allowances (two CAPTCHA providers) are narrow,
single-purpose, and currently dormant (CAPTCHA is off by a prior, documented
decision). No unsafe postMessage/iframe surface, zero dependency CVEs in either
`package.json`.

**PWA/service-worker: two confirmed gaps, both fixed; one deeper lead recorded for
follow-up.** The offline write queue for the Community layer carried no notion of
who enqueued a row - confirmed live with two real members and the app's actual
sign-out/sign-in flow: a comment or a coach's progress entry typed while offline
and still queued when a *different* member signed in on the same device (a shared
coach tablet is the real scenario) would drain under the second member's session,
attributing the first member's words to someone who never sent them. Fixed by
stamping the enqueuing member's own id onto every queued write and refusing to
send a row for anyone else - it stays queued, untouched, rather than being sent
under the wrong identity or silently dropped. Separately, the service worker's
cache-write check didn't verify a revalidation response actually came from the
requested URL rather than a same-origin redirect target - closed the same way
round 3 closed a related gap, as a defense-in-depth tightening (no path was found
by which this app's real hosting could produce such a redirect today). A related,
deeper question - whether the separate, older private-training-log sync queue has
the same identity-binding gap - was raised but not confirmed or fixed: it
intersects with a broader question of how this app's local, single-device data
model is meant to behave when more than one member uses the same device, which
needs a product decision before a real fix, not a queue patch.

**Final assume-breach verification pass: today's fixes hold.** Every guard closed
across rounds 1-4 - the coach-congratulate claim, the PR/achievement forgery
trigger and its one narrow exemption, Storage bucket path-ownership and size/type
caps, moderation authorization and the new notification-redaction pin, the emom
array size guard, and a coach-role-grant boundary chosen as a free pick - was
re-tested by directly calling the real RPC as a real, unprivileged impersonated
caller with zero client-side state, bypassing any UI assumption entirely. All of
them refused or behaved correctly. One documented nuance, not a regression: the
transaction-local "pins" several of today's fixes use are, as raw Postgres
settings, technically settable by any database role - but there is no path from
this app's real client surface (PostgREST exposes only specific granted
functions, never arbitrary SQL) to ever reach that setting, confirmed by checking
the actual API configuration rather than assumed.

Verified: full suite 1612/1612 (7 new regression tests), full browser-check 41/41.

---

## Security hunt: five-round summary — 2026-09-11

Fifteen independent agents across five rounds, run against this app's own codebase
with production Supabase never touched at any point (every test ran against
`installMockCloud()` and/or the local Postgres/Storage stack). Confirmed findings by
severity, and how each was verified:

**High:** one. A member could forge a PR or achievement share by writing directly to
`workout_posts`, bypassing the RPCs that verify real training/achievement data -
fixed with a server-side claim requiring proof of the real RPC, verified against real
local Postgres.

**Medium:** four. A coach's "congratulate once" cap had no real server-side
enforcement (real local Postgres). Two related file-upload gaps - a spoofable
Content-Type allowlist and client-only EXIF/GPS stripping - closed with a real
magic-byte check and strip (real local Storage). A moderator-removed comment's exact
text survived unredacted in the recipient's notifications indefinitely (real local
Postgres). The offline write queue could send a queued write under the wrong
member's identity if a device changed hands before it drained (a real two-member,
real sign-out/sign-in reproduction, mock-verified).

**Low:** three. A raw JS exception message could reach the screen (mock-verified).
One RPC paid the full cost of an oversized array before its cap discarded the rest
(real local Postgres, with real measured timing). A service-worker cache write
didn't verify a revalidation response's actual URL, closed as defense-in-depth (real
Chromium reproduction on the redirect gap this round; the earlier suffix-match gap
in round 3 was also mock/live-verified).

**Documented, not code-fixed, because the lever does not exist in this repository:**
a login-timing side channel and a signup-based username-enumeration oracle, both
properties of the underlying Supabase Auth service rather than this app's own code,
and both downstream of an already-made, explicit product decision (CAPTCHA declined
for a club this size) - reopening that decision is not this hunt's call to make
silently.

**Verified against real local Postgres** (preferred throughout for anything
touching authorization, RLS, IDOR, or privilege escalation, per the hunt's own
rule): the PR/achievement forgery guard, the coach-congratulate claim, the
notification-redaction pin, the emom array guard, and the full round-5
assume-breach re-verification of all of the above plus Storage RLS. **Mock-only**
(browser-driven, `installMockCloud`): the render-error message fix, the CSP
live-injection tests, and the outbox identity-binding fix (IndexedDB has no local
Postgres equivalent to test against).

**No confirmed gap, this hunt's most common outcome by round:** general
authorization/RLS boundaries (round 1), IDOR/object-reference integrity (round 2),
SECURITY DEFINER privilege-escalation paths and RLS-vs-key-secrecy (round 3),
moderation block-enforcement and restricted-member RPC bypass beyond the
notification finding (round 4), and third-party/supply-chain integrity (round 5).

**Areas that would benefit from a follow-up round**, all explicitly flagged during
the hunt rather than silently dropped:
- The local, single-device training-log sync queue's own identity-binding question
  (round 5's unconfirmed lead) - needs a product decision about multi-member,
  single-device use before a real fix is possible.
- A block's lack of retroactive redaction on pre-block notifications (round 4,
  lower severity than the moderator-removal case that was fixed).
- The image-upload pipeline's lack of a decoded-pixel-dimension cap, a plausible
  decompression-bomb shape that could not be verified without real browser
  image-decode tooling this environment didn't have (round 4).
- Realtime (`postgres_changes`) authorization could not be exercised end-to-end in
  this sandbox across all five rounds - the local Realtime container was never
  available here.

## Capped the announcements archive, the second real "feed too long" contributor — 2026-09-11

Follow-up to the club-WOD toggle fix: the previous entry named a second, separate
contributor to feed length and deliberately held off on it pending confirmation -
the announcements archive below the feed rendered every live announcement in full
(up to 20, `announcements_read`'s own query cap), no collapse. Told to fix it.

The most recent `ANNOUNCEMENTS_ARCHIVE_VISIBLE` (3) still render as before; the rest
sit behind a `<details>` disclosure ("עוד הודעות (N)"), the same pattern
`renderAuditLog()`'s own "עוד סינונים" already uses - nothing is hidden, only
de-prioritized past the first screenful.

**Caught before shipping, not after**: a closed `<details>` collapses its content to
zero height, and `navigateToNotifTarget`'s `target.announcement` branch only ever
called `scrollIntoView` - a notification deep-linking into an archived (4th-or-older)
announcement would have scrolled to an invisible target, silently. Fixed by opening
the disclosure before scrolling. A new test seeds 4 announcements specifically to put
the deep-linked one past the cap and proves the disclosure opens, not just that the
node exists in the DOM.

Verified: new tests in `community-notifications.test.mjs` (the cap + the deep-link
fix) and `community-club-wod-board.test.mjs`/`community-club-features.test.mjs`
(unaffected, re-run for confidence), full suite 1606/1606, and a direct visual check
(real Chromium) of the collapsed and expanded states.

## Security hunt, round 4: moderation bypass, client-side tampering, and resource exhaustion — 2026-09-11

Three more independent agents: moderation/abuse-bypass, client-side data tampering, and
resource exhaustion from malicious input.

**Client-side data tampering: one confirmed high-impact gap, fixed with the same
claim-before-write pattern this hunt has used all along.** Sharing a PR or an
achievement is meant to go through server-side RPCs that read a member's own real
training/achievement record before minting the card. Confirmed live against real
local Postgres: a direct table write - any member's own devtools, bypassing both
RPCs entirely - could mint a PR or achievement card with a completely fabricated
result, movement name, and backdated date, and zero backing record. The card then
received the same feed-ranking boost and public-profile placement as a genuine
share. Fixed with a server-side guard requiring proof the row came from the real
RPC before the label is allowed to land, the same transaction-local claim pattern
this codebase already uses for exactly this class of problem - with one narrow,
explicitly-scoped exception preserved for a pre-existing, already-documented
legacy sharing path that has never had server-side verification (a client-only,
self-reported local badge, trusted at the same level this codebase has always
trusted a member's own logged workout - not a new gap, and not touched by this fix).

**Moderation/abuse-bypass: one confirmed gap, fixed.** A comment or post's text is
snapshotted into a notification the moment it's created; nothing ever revisited
that snapshot afterward. Confirmed live: a moderator removing a comment correctly
hid it everywhere the comment itself is read, but the exact original text -
including a comment reported and removed for being abusive - stayed fully readable
in the one recipient's Notification Center indefinitely. Comment and post removal
now blank that snapshot; restoring the content does not restore the notification
text. A related, lower-severity gap in the same family - a block does not
retroactively redact the blocked party's pre-block notifications - is recorded for
a follow-up rather than fixed here; everything created after a block is already
correctly refused.

**Resource exhaustion: one confirmed low-severity gap, fixed; one lead recorded
for follow-up.** One RPC accepted an array field and discarded everything past
its real 20-item limit only after fully expanding the input, so a multi-million-
element array cost real, measurable database time before being discarded -
bounded in practice by this codebase's own statement timeout and per-endpoint
rate limit, so not an outage risk, but inconsistent with the size-check-before-
expand pattern every other array-accepting endpoint here already follows. Fixed
to reject a wildly oversized array outright before any expansion; every
legitimate input, including a real near-miss over the item cap, is completely
unaffected. A second, unconfirmed lead - the image-upload pipeline caps
compressed file size but not decoded pixel dimensions, a plausible
decompression-bomb shape - could not be verified in this environment (no browser
automation available for a real image-decode test) and is recorded for a
follow-up with proper browser tooling rather than acted on without confirmation.

**Moderation/abuse-bypass agent, IDOR-adjacent checks, and business-logic checks
otherwise found clean** - block enforcement holds everywhere going forward,
restricted members are refused server-side on a direct RPC call (not just hidden
in the UI), and every text/array field checked elsewhere carries its own
server-side cap independent of the client's.

Verified: full suite 1605/1605 (11 new regression tests), full browser-check 41/41,
`supabase test db` 3356/3356 against real local Postgres.

## Real device feedback: a real missing toggle, this time confirmed and fixed — 2026-09-11

Two screenshots from the live app: the club-modules panel, and the Feed tab's empty
state for a feature it doesn't list - "לא נקבע אימון למועדון היום" (the daily club-WOD
strip: a coach schedules a catalogue workout for today, it gets one feed card and one
board, members attach results they already logged with one tap, no post required).
Checked against the actual code rather than assumed: `renderClubWodTodayStrip()` and
its loader (`loadClubWodBoards()`) had no `isModuleEnabled()` check at all, anywhere -
unlike every other real feature on this panel, an admin had no way to turn this one
off. A previous pass this session concluded the panel was complete after verifying its
existing 13 toggles all render; this feature was missing entirely from that count, not
just from the panel, which is why it was missed rather than found.

Added `club_wod` to `CLUB_MODULE_TOGGLES` (`clientOnly: true`, matching `directory`'s
own reasoning - no RLS clause to pair a pure UI hide with; `club_wod_boards`/
`club_wods_list` carry their own independent auth checks). Off hides the ongoing
prompt/today-card and skips the round trip that would have populated it - past feed
posts and boards a WOD already generated are untouched, the same "off hides new, not
old" rule `achievements`/`challenges` already follow. `loadClubWods()` (the shared
workout CATALOGUE feeding app.js's own WOD picker) is a separate, more foundational
feature and was deliberately left alone - turning off the daily scheduling prompt
should not also empty a member's personal workout catalogue.

Asked in the same message to look at the feed's overall length: the existing
`railInterleave()`/`RAIL_ABOVE_FEED` budget (only the first 2 non-empty rail cards
render above the feed; the rest interleave a few posts down) already exists
specifically for this, and correctly gets more effective for a club that turns this
new toggle off. A second real, separate contributor was found but not touched without
asking first: the announcements archive below the feed renders up to 20 full cards
(title + complete body + author) with no cap or collapse - a deliberate placement
("reference material," per its own comment) but an uncapped list length nobody
decided on. Flagged for the product owner rather than assumed.

Verified: the two directly affected test files (`community-club-wod-board.test.mjs`,
`community-club-features.test.mjs`, whose 13-toggle count assertion is now 14) plus a
new dedicated test proving the toggle actually skips the network call when off, not
just the render - both green, full suite otherwise unaffected.

## Security hunt, round 3: authentication abuse, privilege escalation, and client-side posture — 2026-09-11

Three more independent agents: authentication/account-recovery abuse, SECURITY DEFINER
privilege-escalation testing, and client-side security posture.

**SECURITY DEFINER / privilege-escalation: no confirmed gap.** Reviewed every
multi-branch definer function where a lower-privilege caller might reach a
higher-privilege code path via an argument combination the UI never sends -
moderation, invite/role-escalation, club WOD, challenge-team, and coach-signal
clusters. Every branch that does more than its own top-level gate justifies
re-checks its own permission independently; the few genuinely asymmetric branches
(attach vs. detach content, member vs. per-person invite role tiers) are asymmetric
by explicit, commented design with the narrower side independently enforced. One
combination not previously exercised by a real caller identity (`head_coach`/`staff`
attempting the admin-only invite role) was verified live against real local
Postgres and correctly refused.

**Client-side security posture: no confirmed vulnerability; one defense-in-depth
gap closed.** The CSP was tested with real injection attempts (inline scripts,
external script/fetch/form-action/object loads) through a live Chromium page, not
just read - every attempt was actually blocked, confirmed via CSP violation events
and network-level request failures. Confirmed live against real local Postgres/REST
that the public anon key alone, with no session, grants zero access to any table or
function - RLS plus table-level grants, not key secrecy, is what protects data.
Verbose server errors: none of today's newer code paths (this hunt's own round-2
upload/coach-congratulate work included) let a raw database error reach a member;
every error path already routes through this codebase's existing safe-fallback
helpers. Service-worker cache-poisoning: the one theoretical mismatch (a cache
lookup that ignored the query string paired with an exact-URL cache write) was
built out as a real live test and found not exploitable, since the canonical app
shell is always precached before the service worker can intercept anything. A
separate, currently-unreachable looseness was found and closed anyway: the
service worker decided whether a same-origin request was an app-shell file by
checking whether its path merely *ended with* a precached filename (so
`/anything/app.js` would have counted the same as the real `./app.js`), rather
than matching the exact resolved path. No code path in this app currently
constructs a request that could reach that gap, but it was strictly looser than
the actual set of precached files and cheap to tighten outright.

**Authentication & account-recovery abuse: two confirmed findings, both inherent to
the underlying auth service rather than this app's own code, and both already
covered by a deliberate, previously-recorded product decision.** A login-timing
difference lets a caller distinguish a real member handle from a nonexistent one
(the auth service's own credential-verification cost, not app logic), and the
account-creation flow lets a caller confirm whether a given handle is already
registered, with no throttling, before any invite code is presented - unlike this
app's own invite-code redemption, which is real, server-side, rate-limited and
already covered by tests. Both trace back to the same root cause already evaluated
and knowingly accepted in an earlier hardening pass (CAPTCHA on the auth service's
own signup endpoint, declined as disproportionate for a club this size) - there is
no lever in this repo's own migrations or client code that closes either one
without reopening that decision, so neither was patched this round; both are
recorded here for visibility rather than left undocumented.

Verified: full suite 1604/1604 (3 new regression tests), full browser-check 41/41.

## Security hunt, round 2: business-logic abuse, IDOR, and file-upload security — 2026-09-11

Three more independent agents: business-logic abuse/rate-limit bypass, IDOR/object-reference
integrity, and file-upload security.

**IDOR/object-reference integrity: no confirmed gap.** Every uuid-parameter RPC and
foreign-key-scoped RLS policy checked resolves ownership/visibility server-side; no
surface let a caller substitute another member's or another club's id to read or
write across a boundary.

**Business-logic abuse: one confirmed gap, fixed with a real server-side unique
constraint, not a client-side idempotency key.** A coach's "congratulate once" cap
on the Coach Dashboard's Celebrate feed was enforced entirely client-side - an
exact-body-text lookup plus in-memory state. Confirmed live against real local
Postgres: calling the underlying comment/post RPC directly (bypassing the UI
entirely, the same thing any member's own devtools console can already do) produced
real duplicate congratulation comments with no server-side objection, and inflated
the exact metric the admin analytics dashboard reports per coach. A client-supplied
idempotency key would not have closed this - the caller controls that value too, and
can just omit or randomize it. The real fix is a dedicated table with a unique
constraint on (coach, kind, target member, the actual moment being celebrated),
claimed atomically before any comment/post is written, mirroring this codebase's own
existing once-per-achievement pattern. A second call for the same real event, from
any source, now claims nothing and writes nothing.

**File-upload security: two confirmed gaps sharing one root cause, both closed with
one new server-side backstop.** The composer/avatar upload pipeline's "images only"
validation and its EXIF/GPS-stripping privacy behavior are both purely client-side
properties of the browser upload path - confirmed live against the real local
Storage container: a direct authenticated upload with a spoofed `image/jpeg` header
got raw non-image bytes past the bucket allowlist, and a real photo with GPS EXIF
was stored and later downloaded byte-for-byte untouched by a second member, despite
the upload pipeline's own documented promise that this never survives the round
trip. Closed with a new Edge Function, invoked asynchronously after every write to
either photo bucket, that verifies the object by its actual bytes (not the header
the uploader chose to send) and strips EXIF/metadata segments before anything else
can read it back - a real signature check and a real strip, not a client-side
promise with no server behind it.

Verified: full suite 1601/1601 (7 new regression tests), full browser-check 41/41,
`supabase test db` 3327/3327 against real local Postgres.

## Security hunt, round 1: authorization boundaries, injection, and data exposure — 2026-09-11

Started a new, separate 5-round pass focused specifically on security (defensive
testing of the team's own app — authorization, injection, data exposure — not the
UX/functional-correctness lens the prior five rounds used). Ran three independent
agents in parallel: authorization/RLS boundary testing (verified live against real
local Postgres, not just the mock), XSS/injection surface, and sensitive-data
exposure.

**Authorization/RLS: no new confirmed gap.** This codebase had already been through
five prior security-hardening passes with real-Postgres verification; this round's
agent independently re-verified several specific surfaces live (club WOD result
visibility, attendance-log role/ownership scoping, challenge team-assignment
gating) rather than trusting the prior record, and confirmed all of them still hold.
One environment limitation flagged, not a vulnerability: the local Realtime
container is stopped in this sandbox, so `postgres_changes` authorization on the
published tables couldn't be exercised end-to-end this round - worth a follow-up
once that's available.

**XSS/injection: no exploitable vulnerability found.** Every user-controlled surface
tested live (post/comment bodies, mentions, display names, bios, imported-backup
content, the `?invite=` boot param) escaped correctly with no payload execution.
Two defense-in-depth gaps closed anyway, since neither is currently exploitable on
its own but both are cheap to close outright:
- An event's map link was rendered as a clickable `href` with no scheme check at
  the render site itself - two independent upstream controls (a client submit-time
  check and a DB `CHECK` constraint) already prevent a non-`http(s)` value from
  ever reaching this field today, but a third, independent gate right at the render
  call means a future write path that bypasses both of those still can't turn this
  into a stored javascript-URI link.
- A CSS selector built from an attacker-reachable value (`?notif=` → a post id)
  used a naive manual escape instead of the shared `cssSel()` helper this codebase
  already provides for exactly this. `querySelector` can't execute script from a
  malformed selector either way, but this closes the inconsistency.

**Sensitive-data exposure: one confirmed low-severity finding, fixed.** A render
failure showed the raw JavaScript exception message on screen - not an injection
risk (already HTML-escaped by a prior pass), but the message text itself could name
an internal property or variable a member was never meant to see. Now shows a
plain, generic message; the console still gets full detail for debugging. Every
other surface checked clean: invite/push deep-link params are stripped from the URL
before first paint and never resurface via back/forward, no secret sits in
localStorage/IndexedDB, and every error path (login, invite redemption, a forced
raw-Postgres-shaped RPC error) already routes through the app's generic,
anti-enumeration message text rather than echoing server internals.

Verified: full suite 1595/1595 (3 new regression tests), full browser-check 41/41.

## A fifth and final live bug hunt round: theme/visual regression, onboarding & account-recovery depth, and resilience under stress — 2026-09-11

Ran the fifth and final round of three independent agents in parallel driving the
real app live in Chromium against the mocked backend (never production): theme/
visual regression across tablet widths, onboarding & account-recovery depth, and
resilience under stress (rapid dialog cycling, flaky-network simulation, sustained
interaction, render-throw recovery). 6 confirmed findings, all fixed with regression
tests - closing out this 5-round pass at 38 confirmed, fixed bugs total (15 from
rounds 1-2, 9/8/6 from rounds 3/4/5):

- **Every dialog in the app was uncapped in width across the ~480-899px tablet gap**
  - `.modal-sheet`'s width cap only ever existed inside the ≥900px desktop block;
  `#app` itself stays locked to its mobile 480px measure the whole way up to that
  breakpoint, so a Settings/picker/WOD-builder/achievements/notification/invite sheet
  stretched to the full viewport instead - measured live at 700px wide on a
  700px-wide viewport, sitting on top of a page still visually a narrow mobile card.
  Capped at 512px (the same #app-content-measure-plus-padding formula the ≥900px
  block's own 592px already uses, just for the range below it) in the base rule,
  leaving the existing desktop cap untouched.
- **Printing the invite QR flyer produced 1-2 extra full-bleed solid-navy pages** -
  the `@media print` block reset `body`'s background but not `html`'s, and both
  inherit the app's live (dark, by default) theme background. Confirmed via an
  actual print-to-PDF render, not just computed styles.
- **An invite code typed with any uppercase letter was rejected with a misleading
  generic error** - codes are minted lowercase-hex only and the server's format gate
  is a lowercase-only regex, so a case mismatch (mobile autocapitalize on the first
  character; retyping a spoken/printed code) silently hashed to a different code
  entirely. The `?invite=` deep-link path already normalized this; manual entry, the
  far more common path, did not. Added `.toLowerCase()` plus `autocapitalize="off"`
  on the input as defense in depth.
- **Rapid double-tap on invite-code submit fired the redemption RPC twice** with no
  in-flight guard - the real RPC increments a shared code's use count before its
  insert, risking an extra use burned off a limited-use code for one real redemption.
  Added a busy guard, same shape as `reactionBusy`/`followBusy`.
- **A failed automatic recovery-verification attempt was silently overwritten by
  "Profile saved"** - `saveProfile()`'s own unconditional success message clobbered
  `verifyRecovery()`'s "verification failed, try again" message, on exactly a brand-
  new member's first automatic verification attempt (the flaky-connection case). The
  gate and its retry button still worked correctly; only the status text was wrong.
- **`ensureCommunityDataLoaded()` had no top-level error handling** - every
  individual loader already normalizes a real network failure into a resolved error
  object (confirmed by reading the vendored SDK), so this isn't reachable through an
  ordinary hiccup, but if some other bug ever threw inside one of the ~17 parallel
  loaders, the old finally-only version still marked the batch permanently loaded
  (blocking any retry for the session) while the exception itself became an
  unhandled rejection. Now caught, logged, and not marked loaded on failure.

Also confirmed clean across a wide sweep with no fixes needed: theme switching
mid-session on every major screen/dialog (including auto/OS-follow mode), rapid
25-cycle dialog open/close (no leak, one-time lazy DOM fill only), a slow/degraded
network (loading states and retry all correct), 66 real actions in one sustained
session (zero console errors), and the render-error-boundary recovering gracefully
for three independent tab paths beyond the one round 4 had already checked.

Verified: full suite 1592/1592 (7 new regression tests across
`test/live-bug-hunt-round5.test.mjs`, `test/community-invite-code-draft.test.mjs`,
`test/community-recovery-method.test.mjs`), full browser-check 41/41 (one new
script, `tablet-modal-width-and-print.mjs`, covering the two CSS fixes jsdom
cannot see).

## A fourth live bug hunt round: notifications depth, moderation & blocking depth, and data-integrity edges — 2026-09-11

Ran three more independent agents in parallel driving the real app live in Chromium
against the mocked backend (never production): a notifications deep-dive, moderation
& blocking depth, and data-integrity edges (malformed imports, two-tab concurrency,
mid-frame render failures). 8 confirmed findings, all fixed with regression tests -
one of them a real Postgres migration, not just a client fix:

- **Blocking a member was permanent - there was no unblock() function anywhere in the
  app**, no "blocked members" list, nothing on the full profile overlay. Confirmed
  live: a one-way action recoverable only via direct database access. Added
  `unblock()`, a `blockedByMe` state slice (distinct from `blockedIds`, which
  deliberately merges both block directions for the comment/reaction-hiding check -
  only a block the viewer actually initiated is theirs to undo), and a "חברים
  חסומים" panel on the Account tab that renders nothing at all when the member
  hasn't blocked anyone.
- **A resubmitted report on already-reviewed content was silently swallowed forever**
  - `report()`'s `ON CONFLICT` clause has always refreshed reason/details on a
    duplicate but never touched `status`, so a dismissed report stayed dismissed even
    when the same reporter came back with a genuinely escalated complaint. Fixed with
    a real migration (`202609110001_report_reopen_on_new_complaint.sql`, verified
    against local Postgres via `supabase test db`, 95 files / 3301 pgTAP assertions
    passing): a resubmission that genuinely changes reason or details now reopens an
    already-closed report; an exact repeat of the identical complaint does not (guards
    against a bad-faith reporter spamming identical resubmissions to force review
    churn). Mirrored in `mockSupabase.mjs` and an existing pgTAP test updated to match
    the corrected behavior.
- **`feed_activity` notifications could never be muted at all** - its preference key
  was the orphaned pre-rename `"comments"` (COMM-218/219 renamed every other type's
  key but missed this one), and no toggle in the Preferences panel ever wrote that
  key regardless. Now keyed to `notif_pref_key()`'s real identity-fallback
  (`"feed_activity"`) with its own panel row, same shape `weekly_recap`/
  `streak_at_risk` already use.
- **A realtime-arriving batched notification silently collapsed an already-expanded
  group mid-read** - the group's "is it open" key was derived from its own first
  row's id, which changes the instant a realtime INSERT unshifts a new row onto the
  front. Now keyed off the group's last (oldest, stable) row instead.
- **The header bell's badge wasn't actually real-time until Community had been
  visited at least once that session** - the unread *count* was already eager
  (promoted into the session-start batch specifically so the badge is correct on
  first paint), but arming the realtime *subscription* that keeps it live was only
  ever wired into the deferred, Community-visit-gated batch. Promoted alongside the
  count, for the same reason.
- **A mention/comment notification whose target post wasn't on the currently-loaded
  feed page silently did nothing** - closed the notification center with zero sign
  anything was even attempted. Now shows an honest "not loaded right now" message
  instead.
- **Blocking someone mid-conversation blanked the whole open comment thread to
  nothing** until manually closed and reopened - reactions self-heal from a block's
  cache wipe (`ensureReactionsLoaded()` runs unconditionally every render) but
  comments never had the equivalent. Added `ensureCommentsLoaded()`, same shape.
- **Editing an entry on a device with two tabs/windows open against the same
  IndexedDB origin could silently discard a sibling tab's edit** - `startEditEntry()`/
  `startEditWodEntry()` seeded the edit form from the in-memory `entries`/`wodEntries`
  array, which can go stale for a whole session with no cross-tab sync on the
  pure-offline path. Both now re-read the current on-disk record the instant editing
  begins (both became `async`; every existing call site across the test suite needed
  the same `await` added - a genuinely wide mechanical fix, caught by re-running the
  full suite before considering this done).

Verified: full suite 1588/1588 (11 new regression tests across
`test/live-bug-hunt-round4.test.mjs`, `test/community-engagement-cluster.test.mjs`,
`test/community-notifications.test.mjs`, `test/community-moderation.test.mjs`), full
browser-check 40/40, `supabase test db` 95/95 files (3301 pgTAP assertions).

## A third live bug hunt round: achievements/streaks depth, the WOD catalogue, and search & discovery — 2026-09-11

Ran three more independent agents in parallel driving the real app live in Chromium
against the mocked backend (never production), each reading the existing
tests/browser-check scripts for its area first so nothing already-covered got
re-reported: an achievements/streaks deep-dive, WOD/benchmark catalogue edge cases,
and search & discovery across the movement picker, WOD picker and Community's member
directory. 9 confirmed findings, all fixed with regression tests:

- **A set saved after the real day changed, with the date field never touched, was
  silently dated with yesterday's date.** `logDate`/`wodLogDate` are captured once at
  page load and read again at save time — a session left open across midnight (the
  ordinary "phone stayed on all night" case, not an edge case) meant the entry's date
  quietly went stale, with the very next save correcting itself and leaving no sign
  anything had gone wrong. Added `logDateExplicitlyChosen`/`wodLogDateExplicitlyChosen`
  flags, mirroring `movementExplicitlyChosen`'s own shape: only an actual touch of the
  date field (or opening a real past entry for edit) counts as explicit; everything
  else reads `todayISO()` fresh at the moment of save.
- **An already-earned, already-celebrated PR-tier badge could be silently re-locked**
  by an unrelated edit to an older entry — `categoryPRCounts()` recomputes from
  scratch on every render, so correcting a typo in an old set could drop the live
  count back under a tier's threshold, regressing the displayed badge (and the
  athlete score/level computed from the same map) with no notice. `seenAchievementIds`
  already tracks "has this ever been true" (added the moment a badge is first
  detected, never removed) — `renderAchievementsContent()` now ORs it into `earned()`
  instead of trusting the live recompute alone, so a medal stays earned once won.
- **A celebration deferred behind an open dialog (Achievements, Settings, a picker...)
  was only flushed by a literal click** — closing that dialog via Escape or the
  hardware/gesture back button left it stuck until some later, completely unrelated
  click happened to trigger it, popping up disconnected from the moment it was
  actually earned. `flushDeferredCelebration()` is now also called from both the
  Escape keydown handler and the popstate/back-button handler, not just
  `closeOnboarding()` and the generic click handler's tail.
- **The day list's flame icon, the calendar's per-day PR dot, and its "ימי שיא" stat
  all read the raw, ungated `entry.isPR` flag** — unlike every OTHER PR-count/badge
  surface, which already goes through `celebratablePrEntryIds()`'s
  `MIN_ENTRIES_BEFORE_PR` gate. A movement's trivial first-ever entry showed a
  "record" flame, and an entry's flame never cleared even after a later edit made it
  no longer the real running max (`renderDetailCard()`'s own history chart was
  already correct here — it recomputes fresh and never reads the stored flag). New
  `isFlameworthyEntry()` helper, reused across all three surfaces.
- **Building a custom WOD with a name that already exists silently discarded
  everything just built** (format, movements, EMOM rotation, time cap...) and swapped
  in the pre-existing WOD instead, with zero message. The redirect-to-existing
  behavior is unchanged; `addCustomWod()` now tells the member via toast.
- **Undoing a deleted WOD attempt after its own WOD definition was ALSO deleted in the
  undo window resurrected a permanently orphaned entry** —
  `deleteCustomWod()`'s history guard only sees `wodEntries` as they exist at the
  moment of deletion, and an entry sitting in the 5-second undo window has already
  been filtered out of that array by then. `restoreWodEntry()` now refuses (with an
  honest toast) when its own WOD no longer exists, instead of creating a "?" row that
  was invisible in History, permanently stuck in the calendar, and a silent no-op to
  edit.
- **Rx and Scaled attempts were compared as one pool for "the" WOD record**, despite
  being treated as meaningfully different everywhere else in the app (a dedicated
  toggle, the "· מותאם" tag, a separate `scaledWeight` field) — a faster Scaled time
  could flash "new record" and overwrite the displayed Rx best, and conversely a
  genuine Rx improvement could be wrongly denied PR status because an unrelated
  faster Scaled attempt sat in the comparison. `bestWodScore()` now takes an optional
  `rx` filter; `saveWod()`'s PR check and `formatWodBest()` (which now prefers the Rx
  best, falling back to Scaled only when no Rx attempt exists) both use it.
- **The WOD history chart's PR dots used an inclusive (`&lt;=`/`&gt;=`) comparison**,
  disagreeing with the real stored `isPR` flag's strict one right in the attempt list
  below it — an exact tie flashed as a second PR dot on the chart while the list
  correctly showed only one flame. Now strict, and Rx/Scaled-aware to match
  `bestWodScore()`'s own fix.
- **Community's member Directory search box showed "אין חברים להצגה" (no members) for
  a search that matched nobody** — the exact same class of bug COMM-377 already fixed
  for the admin roster, just never propagated to this second search surface (a
  separate code path, `renderDirectorySection()`/`directoryRows()`). A member whose
  search typo matched nobody read it as "this club's directory is broken." Now a
  distinct `data-directory-empty="no-results"` state with its own copy.

Verified: full suite 1578/1578 (9 new regression tests: 8 in the new
`test/live-bug-hunt-round3.test.mjs`, 1 appended to
`test/community-members-directory.test.mjs`), full browser-check 40/40.

## A second live bug hunt round: sync/PWA lifecycle, keyboard a11y, and lightly-covered admin areas — 2026-09-11

Asked to keep looking for more live bugs. Ran three more independent agents in
parallel, each covering fresh ground the first round hadn't: the offline-first
sync/service-worker machinery, keyboard/accessibility navigation, and the two admin
areas an earlier agent had flagged as only lightly checked (Club WOD board, invite
management) plus the whole app at desktop viewport width. 7 confirmed findings, all
fixed:

- **The update banner's "wait for a tap" promise was defeated by the very next screen
  lock/unlock.** `showUpdateBanner()` never marked itself as showing, so the same
  `visibilitychange` listener that legitimately auto-applies an update arriving while
  the page is hidden also fired on the NEXT visibility change after the banner was
  already up - an ordinary phone screen lock (explicitly named in the code's own
  comment as the common case) silently reloaded and dropped unsaved input, with no tap
  ever happening. A new `updateBannerShowing` flag makes only an actual tap on the
  banner able to apply it from that point on - confirmed live with real unsaved text
  sitting in the WOD builder's name field. `update-flow.mjs`'s own Scenario 3 used to
  assert the buggy behavior as correct; rewritten to assert the fix instead.
- **Opening the WOD builder from inside the still-open WOD picker** left both dialogs
  "open" at once - same root-cause shape as the earlier achievements/nav-menu bug.
  `currentAppDialog()` kept treating the now-invisible picker as "the" open dialog:
  Escape closed the hidden picker first (a second press was needed for the visible
  builder), Shift+Tab from the builder's first control tabbed into the hidden picker
  instead of wrapping, and the scroll lock dropped one press early. Fixed the same way
  as before: close the picker first.
- **The Club WOD publish/republish form could be silently wiped mid-edit** by an
  unrelated global toast's 6-second auto-clear timer, which triggers a full rerender
  from the form's own stale, uncontrolled state. Now kept live-synced the same way
  `inviteCodeDraft`/date-echo fields already are.
- **Creating a shared join-code collapsed its own one-time reveal card**, and the
  reveal's close button became genuinely unreachable - the `<details>` disclosure it
  lives inside had no id and no tracked open state, so `createInviteCode()`'s own
  success rerender rebuilt it plain-closed. Since the raw code is never shown again
  after this screen, that risked losing it outright. Now tracked the same way
  `manageAdminArea()`'s five accordion areas already are, forced open the moment
  there's a reveal to show.
- **Shared codes showed no distinction between healthy, exhausted, and expired** -
  `active` never auto-flips on either condition, and the badge only ever printed that
  raw boolean. Now derived client-side from the same use_count/max_uses/expires_at the
  row already displays as text.
- **Invite/shared-code creation forms rendered ~874px-wide inputs** in the ≥1200px
  staff-tier admin column (a width meant for genuinely tabular work - roster,
  moderation, analytics - not a single-field form). Capped to match `.save-btn`'s own
  established narrow-form width.
- **A record with no stored `ts`** (legacy pre-existing local data, or a hand-restored
  import) got a fresh, unstable `Date.now()` manufactured on every load, feeding
  directly into cross-device last-write-wins conflict resolution - a years-old
  workout could look like it was just edited, every session, with a different value
  each time. `cleanTs()` now derives a stable fallback from the record's own date when
  one is available, so the same input always produces the same output.

Verified: full suite 1569/1569 (4 new regression tests), full browser-check 40/40
(two new scripts: `desktop-invite-form-width.mjs`, and `update-flow.mjs`'s Scenario 3
rewritten in place).

## A full site-wide live bug hunt, three fresh agents actually using the app — 2026-09-11

Asked to check the whole site again for live bugs. Ran three independent agents in
parallel, each driving the real rendered app in Chromium against the mocked backend
(never production) rather than reading code: core training log, Community's
member-facing surfaces, and Community's coach/admin surfaces. Fixed all 8 confirmed,
reproduced findings:

- **Rapid double-tap on the save CTA created duplicate entries** - `saveSet()` and
  `saveWod()` had no in-flight guard at all; two overlapping clicks each created their
  own fresh entry. Same in-flight-guard shape as cloud.js's `reactionBusy`, via a
  `try`/`finally` around each function so every existing early-return path still
  releases it.
- **A fresh measurement type's save button silently did nothing at its default 0
  value** - now disabled at 0, kept in sync as the stepper moves (its own tap handler
  patches the DOM in place rather than triggering a full render, so the button's
  disabled state has to be updated from that same place).
- **Deleting a single measurement value had no confirmation and no undo** - the only
  destructive action left in the app without either. Mirrors `askDeleteEntry`/
  `restoreEntry`.
- **"מחיקת כל הנתונים" left Settings and the re-triggered Welcome modal open at the
  same time** - Settings is now explicitly closed first.
- **A club announcement could silently lose everything past 1000 characters, mid-word,
  with no ellipsis** - the composer allowed 2000 while every feed card's own render
  path (`postBodyHtml()`) has always capped display at 1000. Capped the composer to
  match what actually displays, like every other post-composing surface already does.
- **The Follow button never reflected whether you already followed someone, anywhere
  in the app** (directory, welcome post, classmates card, member row, profile dialog)
  **and had no in-flight guard** - a second, well-intentioned tap on a button that
  never visibly changed silently unfollowed the person (the insert's 23505 conflict is
  deliberately turned into a delete), with an identical toast either way. Added a
  `followingIds` cache (loaded once, updated optimistically) and a `followBusy` guard,
  both read through one shared `followButtonHtml()` every call site now renders
  through, plus distinct follow/unfollow toast copy.
- **The coach "Welcome" tool had no duplicate-send guard beyond one in-flight lock** -
  once a call finished, a fresh tap (or the same state after navigating away and back)
  could spam unlimited duplicate welcome comments on one member. The guard now lives
  in `welcomeNewMember()` itself, the one write path both the dashboard button and a
  separate feed-card button share, with the dashboard's own welcomed-state
  reconstructed from real server data the same way Celebrate/Engage already are.
- **Hitting the 3-pin cap failed silently outside the Feed tab** - the error only ever
  rendered inside the Feed tab's own club rail, so pinning from a challenge/event
  dialog just looked like the tap did nothing. Routed through `setMessage()`, this
  app's one genuinely global, viewport-anchored notice channel - the same one the
  success case already used.

Verified: full suite 1565/1565 (12 new regression tests, one per fix plus a couple of
paired controls), full browser-check 39/39.

## Edge-swipe-back was falling through to the OS on an ordinary screen — 2026-09-11

Live report: "when I move my finger from the left side it opens another app or
something." manifest.json ships `display: standalone` - an installed PWA's
WKWebView still recognizes iOS's own edge-swipe-back gesture even though it shows no
browser chrome for it. This session's earlier dialog back-button fix (see below) only
ever pushed a history entry while a dialog was open, consumed back to zero the
instant it closed - so on any ORDINARY screen, with nothing open, history had
nowhere to go, and an edge-swipe-back gesture fell straight through the page to the
OS (backgrounding the installed app / the app switcher) instead of being absorbed.

Fix: one un-consumable history anchor established at boot (app.js, right after the
existing notif-deep-link URL cleanup, and after cloud.js's own invite-code cleanup -
both scrub a live credential from the address bar via `replaceState` before anything
should be allowed to `pushState` on top and leave the original, credential-bearing
entry reachable underneath forever). A popstate listener re-plants the same anchor on
any pop the dialog-reservation system isn't already handling, so an edge-swipe
attempt always lands back inside the app - the dialog-close feature is unaffected,
since that listener explicitly defers to it (`if (appDialogHistoryPushed) return`)
rather than eating every pop unconditionally.

Real device gestures can't be driven by Playwright, but the exact API surface a
gesture drives (`history.back()` + the `popstate` it fires) can: new
`scripts/browser-check/history-anchor-trap.mjs` drives that directly, paired with a
control proving the dialog-close case still works through the same listener chain
now that a second listener is in the mix.

Verified: full suite 1553/1553, full browser-check 39/39 (new
`history-anchor-trap.mjs`). The underlying gesture-level behavior still needs a real
device to fully confirm.

## Three more live reports: a permanent medal icon, an unreachable close button, and a self-cleaning "what's new" — 2026-09-11

Three issues reported live, back to back, against the changes above:

- **"מה חדש" always dumped its FULL history, forever** - RELEASE_NOTES only ever
  grows, and the render used lastSeenVersion solely to decide whether to tag an entry
  "חדש", never to decide whether to show it at all - so a member who had already
  caught up saw the exact same wall of months-old entries every time ("currently it's
  super old"). `renderNotificationsList()` now renders only entries newer than
  `lastSeenVersion` (what `unseenReleaseNotes()` already computed for the badge), with
  an "אין עדכונים חדשים" empty state once there is nothing left to show - self-cleaning
  per device, no manual pruning of the source array needed. The one now-redundant
  per-item "חדש" tag is gone too, since everything rendered is unseen by construction.
- **"I want a medal icon in the top left... I can't see any change."** The header's
  existing achievements entry point (the greeting button + "לכל המדליות וההישגים שלי"
  link) lives in the header's SECOND child, which is `display:none` on every scene
  page - and all 5 main tabs are scene pages (`PAGE_SCENES`, app.js); only the
  admin-only "ניהול" tab is not. So the entry point a member could actually find was
  invisible everywhere they spend their time. New `#medalsBtn` lives in the header's
  FIRST child instead, next to the existing bell/sparkle icon, and needed a real
  spacer grid column in scene mode (not a 4th zero-gap column) so its box and the
  bell's don't share overlapping tap targets - the same shape a comment elsewhere in
  this header already warns about.
- **"This button can't be reached"** (achievements' own close X, screenshotted
  colliding with the device status bar). `#navMenuSheet`/`#settingsSheet` already had
  a `padding-top: calc(env(safe-area-inset-top,0px) + 16px)` rule for exactly this -
  `#achievementsOverlay`'s modal-head, also full-height with `position:absolute;
  top:0`, was simply missing from that selector list.

Verified: full suite 1553/1553 (including a new PROVEN_SAFE entry for
`app-innerhtml-sinks.test.mjs`, SEC-018's sink-escaping check), full browser-check
38/38 including two new scripts (`header-medals-icon.mjs`, and `roadmap.mjs`'s
notifications section rewritten with a paired empty/control assertion).

## Four extended-use persona reviews, a live achievements bug report, and the stacking bug they found but didn't fix — 2026-09-11

Ran four independent long-session agents (coach, member, admin, trainee) actually using
the app rather than skimming it, each researching its own role first. Fixed everything
they found except one deliberate design choice (Hebrew movement search stays
substring-only, confirmed intentional, not a bug):

- **עיטורים renamed to מדליות** end to end — title, celebration copy, share templates,
  settings labels, audit-log action names — with every adjective/verb re-conjugated
  (עיטור is masculine, מדליה is feminine; "עיטור חדש נפתח" → "מדליה חדשה נפתחה").
- **Achievements was hard to find and, once open, hard to leave.** Root cause of "can't
  close it": the nav menu stayed open underneath it, and the dialog-lookup that decides
  which open dialog owns close/Escape returns the FIRST match by registration order —
  the nav menu, not achievements. `openAchievements()`/`openSettings()` now close the
  nav menu first. Findability: the header's greeting button and a new explicit "לכל
  המדליות וההישגים שלי" link both open it with no menu at all; the nav menu's own
  avatar row now carries a visible "מדליות" label + chevron instead of being an
  unlabeled tap target.
- **No back-button support anywhere in the app.** Neither dialog registry
  (`APP_DIALOGS` in app.js, the separate `CLOUD_DIALOGS` in cloud.js) reserved a
  history entry on open, so a hardware/gesture back press left the app entirely instead
  of closing whatever was open — reported live as "we need to close the app for coming
  back." Both registries now push a history entry on open and consume it on normal
  close, with a `popstate` listener that closes the current dialog (or re-pushes if the
  top dialog isn't escapable). Regression-tested by a new
  `scripts/browser-check/dialog-back-button.mjs`.
- **Coach Celebrate/Engage dedupe was client-memory-only**, so a reload or a second
  coach re-showed an already-congratulated PR or an already-reached-out flag.
  `congratulateCelebrateItem()`/`loadCoachCelebrate()` now reconstruct "already
  congratulated" from a real duplicate-body check against server comments;
  `coachEngageReachOut()`/`loadCoachEngageFlags()` do the same against a new
  `member_contact_log` write.
- **PR-share prompts had no cooldown per movement** — a member logging several PRs for
  the same lift back to back got the share dialog every single time. Added a 7-day
  per-movement cooldown.
- **Achievements gave no "how close am I" signal.** Added `need`/`current` fields to
  the PR/streak/session-milestone tiers and a "next up" nudge on the achievements
  screen.
- **WOD glossary was missing Snatch and Clean & Jerk**, the two lifts the benchmark
  catalogue actually names most. Added both, plus a glossary link from the benchmarks
  section that wasn't reachable before.
- Admin: manage-tab area open/closed state now persists across renders instead of
  re-collapsing on every interaction; the audit log resolves actor names instead of
  showing a truncated UUID; member roster search was added (roster arriving empty vs.
  a search matching nothing are deliberately different states — the former shows no
  message at all, per an existing pinned rule).
- Two mock-vs-real-backend gaps found along the way turned out NOT to be production
  bugs once checked against real local Postgres (`supabase test db`): the "new member
  welcome post" and a "stuck moderation report" case were both mock-fidelity gaps in
  `test/helpers/mockSupabase.mjs`, now fixed there.

**The one item the QA agent flagged but correctly left unfixed, fixed here:**
`body[data-scene] main{ position:relative; z-index:1; }` gave `<main>` its own
stacking context (position:relative + a real z-index does that; position:relative
alone does not). `<header>` (z-index:20) and `#bottomNavWrap` (z-index:30) are main's
siblings, not its descendants, so on every scene page (History, Progress, Library,
Community, Achievements, Add) a dialog's own z-index:50 — rendered into `#content`,
main's child — was capped at main's stacking level of 1 and never actually compared
against the header/bottom-nav at all. The backdrop's top ~64px and bottom ~68px+
safe-area silently ate no taps there. Fix: drop the z-index, keep position:relative —
nothing depended on the z-index; `.scene-page` already has its own `isolation:isolate`
and `.scene-sheet` its own scoped z-index for the photo/scrim layering this looked
like it was meant for. New `scripts/browser-check/scene-dialog-stacking.mjs` hit-tests
under the header and bottom nav with a live dialog open, paired with a control that
re-adds the old rule and proves the same hit-tests fail under it.

Verified: full suite 1553/1553, full browser-check 37/37 (including the two new
scripts above), `check-version`/`check-vendor-version` clean.

## A rerunnable tool for the bugs manual audits keep missing — 2026-09-10

Asked, pointedly: the previous role-coverage pass found two real bugs a fresh set of
eyes had missed; build something that finds them without needing a fresh set of eyes
each time, then run it for real. `scripts/audit-role-coverage.mjs` is a new static
check, not a one-off script - three mechanical checks modeled directly on the three bug
shapes already found this session:

1. **Permission-gate mismatch** — cross-references every render function's `hasPerm()`
   gate against the actual (transitive, through `perform public.other_fn(...)` calls,
   and BRANCH-AWARE per argument value where a decision picker's chosen option only
   surfaces two steps later through a separate confirm control) permission its buttons'
   RPCs require server-side, flagging any control visible to a role the server will
   then refuse.
2. **Type-coverage gap** — for every server RPC with a closed-enum argument guard,
   checks that every value the server accepts has a real client control, not just the
   ones reachable through a direct handler call in a test.
3. **Dead field-registry entry** — flags a `{key, label}` toggle whose key is
   referenced nowhere else in the client, the shape a control for a nonexistent feature
   takes.

**This entry was rewritten once already, mid-session, for overclaiming** - an earlier
draft reported the tool "confirms it now catches both previously-known bugs" without
having actually re-run that comparison carefully enough to notice check 1 didn't. Told
plainly to fix what was actually found rather than just correct the wording, the real
gap got closed instead of documented as accepted: check 1 alone (gate and RPC in the
SAME render function) genuinely could not see the original coach/restrict-button bug,
because that bug is a TWO-STEP flow - clicking a decision only opens a confirm sheet; a
SEPARATE button in a DIFFERENT function reads the chosen decision back out of state and
fires the RPC. A new check 1B now traces exactly that: it finds the option array behind
a decision picker, follows the SAME dataset-attribute name to wherever it reappears as
an RPC argument (`data-decision` <-> `p_decision`, a naming convention this codebase
applies consistently), and resolves the RPC's requirement PER OPTION VALUE rather than
as one union over the whole function - `mod_review()`'s own top-level check is
`comment.moderate` for every decision, and only `restrict_temp`/`restrict_permanent`
additionally require `member.restrict`; unioning the whole function would wrongly make
`remove`/`warn`/`dismiss` look just as restricted.

Getting there surfaced two more real bugs IN THE SCRIPT, both found by refusing to
accept "still doesn't reproduce" as a shrug: a naive "first `end if;`" search for a
branch's own end stopped at a NESTED if/end-if inside an earlier branch, truncating the
chain before it ever reached the branches that mattered; and a recursion bug where the
CALLER pre-marked a callee as "already visited" one line before calling it, so the
callee's own entry guard saw itself as a cycle and returned nothing - silently
weakening check 1 itself for any finding depending on a one-hop callee, not just this
new check. Both fixed. Re-run against `git show b957780:cloud.js` (this repo's own
pre-fix state, via `git show`, never by touching the working file), check 1B now
correctly flags `restrict_temp`/`restrict_permanent` and correctly clears
`remove`/`warn`/`dismiss` - the real bug, the real distinction, genuinely re-caught.

**Along the way it also found a third, real, previously-unknown bug**:
`renderRestrictionsPanel()`'s outer gate is an OR across three tiers (`MEMBER_RESTRICT`
/ `COMMENT_MODERATE` / `isAdmin()`), so a plain coach could see the whole
active-restrictions panel and a real "ביטול ההגבלה" (lift restriction) button on every
row — `mod_lift_restriction()` requires `community.member.restrict` (head_coach+) and
would have refused every coach's click. Same defect class, a sibling panel the manual
pass didn't happen to check. Fixed the same way: the lift button now only renders for a
role that actually holds the permission the RPC will demand.

A full re-run against the CURRENT, fixed tree still returns three findings - the
restrictions-panel one above, plus `restrict_temp`/`restrict_permanent` again. All
three are confirmed false positives under one real, stated limitation: both checks see
a render function's OUTER gate, not a per-value inner `.filter(d => hasPerm(...))`
narrowing what actually renders - exactly how both of these bugs were fixed. Verifying
each finding against the real code, every time, is what caught every other problem in
this entry; this is the one that's left, and the script's own header says so rather
than letting a clean-looking run imply otherwise.

Verified: full suite green (this session's own +1 test for the restrictions-panel fix),
via the working tree, which also carries a concurrent session's own unrelated
in-progress changes to many of these same files — every edit in this entry was
isolated into its own minimal patch, diffed against `git show HEAD:<file>` and applied
with `git apply --cached`, specifically so staging and committing this work would not
touch or discard anything the other session has not committed yet.

## A role-coverage audit — two real bugs found and fixed, one dead control removed — 2026-09-10

Asked to verify the app is actually ready per role, not just told so. Four parallel research
passes each audited one of the four reachable roles (`member`, `coach`, `head_coach`, `admin` —
`staff`/`owner` are seeded in the schema but have no path to being granted, confirmed
out of scope) against `AUTHORIZATION_MATRIX.md`'s own permission truth, reading the actual
render code rather than trusting prior audit docs. Two real, previously-unverified defects
came back, both fixed and covered by new tests, both confirmed live in a real Chromium
session (not just jsdom) before shipping:

- **A plain `coach` saw two moderation-queue buttons that always failed.** `renderModeration()`
  showed all five decisions - including "הגבלת פרסום זמנית"/"הגבלת פרסום קבועה" (restrict,
  temp/permanent) - to any holder of `community.comment.moderate`, which every coach holds.
  But `mod_restrict_member()` independently requires `community.member.restrict`, seeded only
  to `head_coach` and up. A coach clicking either button got a hard, unexplained "not
  authorized" every time - a broken control, not a missing one. The two decisions are now
  filtered on `hasPerm(PERM.MEMBER_RESTRICT)` before they render at all.
- **Content pinning had no real button anywhere except the announcements list.**
  `pin_set()`/`pinTargetLabel()` have modeled four pinnable types (announcement/challenge/
  event/post) since COMM-155 shipped, but only announcements ever grew a pin control - every
  existing pin test for the other three types went through a direct `window.eval` handler
  call because there was no button to click, in this codebase or in production. A shared
  `isPinnedTarget()`/`pinToggleHtml()` pair now backs a real pin/unpin control on a
  challenge's and event's detail-view toolbar and on a post's own "⋯" overflow menu, gated
  on `community.content.pin` (head_coach+) same as it always should have been.
- **A dead privacy toggle removed.** The Account tab's privacy panel offered "אפשר הודעות
  פרטיות אליי" (allow private messages) - a preference for a direct-messaging feature that
  does not exist anywhere in the app. The `profiles.allow_messages` column stays in the
  schema untouched (harmless, ready the day DMs ship); only the misleading client control
  and its now-unnecessary fetch are gone.
- **Investigated and closed, no code change:** the club-modules panel ("no toggle for every
  feature") was re-verified toggle-by-toggle against every `module_key` the schema seeds -
  all 13 (8 community + 5 coach-tools) render as real checkboxes, none missing. The two
  groups sit in one continuous scroll; the most likely explanation is the original screenshot
  simply hadn't scrolled to the second group yet.

Verified before shipping, not assumed: full JS suite 1531/1531 (4 new tests - a coach seeing
the right 3-of-5 decisions, a head_coach pinning a challenge from a real click while a coach
never sees the control, the same for an event, and a post pinned through its real overflow
menu instead of `window.eval`), full browser-check 36/36 tracked scenarios (the 37th failure,
`zz-trainee-tour.mjs`, is untracked WIP left by a concurrent session in this working tree,
reproduced failing identically with none of this pass's changes applied - not a regression,
left untouched), and a live 4-role Chromium walkthrough (member/coach/head_coach/admin,
light and dark) screenshotting the actual fixes working end to end: the coach queue with
only 3 buttons, the head_coach queue with all 5, a challenge going from no-pin-button
(coach) to a working pin→unpin round trip with a real confirmation toast (head_coach), and
the privacy panel's 10 remaining toggles with no dead 11th.

## Real device feedback, two visual fixes — 2026-09-10

Five screenshots from the actual production app on a phone, with three complaints:
no toggle for every feature, the audit log takes over the whole screen, and some text
sits out of place. Two of the three had concrete, fixable causes; the third (a specific
missing toggle on the club-modules panel) needs the member to point at the exact
feature - the panel already renders all eight `CLUB_MODULE_TOGGLES` entries, so nothing
was silently dropped from it.

- **The notification-preferences push button was disabled and unlabeled to nothing
  ("התראת דחיפה · בקרוב")** but still rendered at roughly 3x the width of its
  `in_app`/`off` siblings, unbalancing every row on the panel - the exact "text getting
  not in place" screenshot. `state.featureFlags.notifPush` is off by default in V1 and
  the button did nothing while off, so `renderNotifPrefsPanel()` now omits the push
  option from the DOM entirely while the flag is off, rather than rendering it disabled.
  The subscribe/revoke/deep-link machinery underneath - `notifPushEnabled()`,
  `registerPushSubscription`, `disableNotifPush`, sw.js's push/notificationclick
  handlers, `communityHandlePushDeepLink` - is untouched and still fully covered by
  `test/community-web-push.test.mjs`'s flag-on tests; the moment the flag flips on, the
  same three-button row (push/in_app/off) renders again unchanged.
- **The admin audit log rendered one full row per `admin_actions` record**, so a
  genuinely repeated action on one target (a coach toggling one shared code's status
  several times, say) painted the whole screen with near-identical rows - same label,
  same target, same actor, nothing to tell them apart at a glance. A new
  `groupConsecutiveAuditActions()` collapses a CONSECUTIVE run of the exact same
  `(action_type, target_type, target_id, admin_id)` - rows already arrive newest-first
  from `admin_actions_page()` - into one row carrying a "× N" count and the most recent
  occurrence's timestamp. A genuinely different action, target or actor interleaved
  between two otherwise-identical rows is never merged into either neighbor.

Verified before shipping, not assumed: full JS suite 1527/1527 (one new test seeds a
genuine 3-in-a-row repeat, a different action on the same target, and the same action
on a different target in one seed, proving the grouping neither over- nor
under-collapses; two existing push-preference tests updated from "renders disabled" to
"absent from the DOM"), full browser-check 34/35 (`community-person-invite-lifecycle.mjs`
reconfirmed flaky under `run-all.mjs`'s parallel load, not a regression - passed 3/3 on
its own), and a direct visual check (real Chromium) of the notification panel with no
push button/mention and the audit log collapsing 9 seeded rows to 4 with correct "× 3"
and "× 4" counts.

## A fresh-eyes UX audit, verified and shipped — 2026-09-10

A batch of small, self-contained findings from a genuine first-time hands-on tour of the
shipped app (not a code read) had been sitting uncommitted in the working tree - a
concurrent session's own work, left untouched while it was in progress per this
session's own discipline. Asked to finish it: read every diff in full, verified it
against the real test suite rather than assuming it was done, and shipped it.

- **A member's literal first-ever logged set unlocked "First PR" and the Progress tab
  read "3 שיאים החודש" after one session** - `e.isPR` is honest against everything on
  file, and with nothing on file yet a movement's first few entries trivially beat
  "nothing." `saveSet()`'s own `MIN_ENTRIES_BEFORE_PR` already encoded the right rule for
  the full-screen celebration; a new `celebratablePrEntryIds()` applies that same rule
  everywhere else a PR gets counted or badged (the Progress tab's monthly count, the
  achievement engine's `prTotal`) instead of each reading the raw flag independently and
  drifting from it. The same brand-new-movement's set also used to trigger cloud.js's
  "share this PR with the club?" prompt - a `trivial` flag threads through the
  `PR_CREATED` event so that one consumer skips it, while `onPrCreatedForChallenges`
  (which must stay correct regardless of how many prior sets are on file) ignores the
  field entirely and is untouched.
- **The header's one always-visible bell was wired only to the offline "what's new"
  release notes** - a member could have unread reactions/comments/achievement
  notifications sitting behind Community's own small bell chip with no signal anywhere
  else. Real community notifications now take priority on the header (falling back to
  release notes when nothing's unread there); release notes moved into Settings as a
  permanent row so they don't need header space to stay discoverable. `render()` now
  calls `updateNotificationsBadge()` on every pass, not just once at init, so the badge
  stays honest on every tab.
- **The nav menu sheet was a profile row, one settings link, and a full screen of empty
  navy below it** for a regular member (every real destination already lives in the
  bottom tab bar) - now closes with a quiet "האימוניה · vX.X.X" footer instead of trailing
  into nothing.
- **The desktop sidebar's settings-section header and Community's own "חשבון" subtab both
  read "חשבון"** a few pixels apart, naming two different things once Community is open -
  relabeled to "כללי" (a single settings link is not an account).
- Two grammar fixes ("1 ימים" → "1 יום" on the streak label) and a near-empty progress
  chart (1-2 points) now explains itself ("עוד 2 נתונים ותראו כאן מגמה") instead of just
  looking sparse.

Verified before shipping, not assumed: full JS suite 1526/1526 (11 new/updated tests
covering the PR-triviality fix from both app.js's and cloud.js's side, the header-bell
routing in all four states, and the nav-menu footer/grammar/chart-hint fixes), full
browser-check 35/35 including `a11y-axe-scan.mjs`, and a direct visual check (real
Chromium) of the header bell showing a real unread count and the nav menu's new footer.

## Closed the last flagged-but-unfixed item: an engagement-alert burst guard — 2026-09-10

Asked to fix everything still open. The one remaining item from this session's research
passes: `coach_notify_engagement_flags()` fans out one immediate notification per (flag ×
recipient) pair. Production had zero open flags when this was first flagged, so the very
first real run was a non-event - but the underlying shape stays a real risk going forward:
`coach_detect_engagement_decline()` runs daily regardless of whether anyone's listening,
so any stretch with `engagement_alerts` disabled (the admin toggle this feature shipped
specifically so an owner could turn it off) silently accumulates un-notified flags, and
re-enabling it would dump the whole backlog as N separate pings in one run.

Considered and rejected reusing the generic cross-type `notification_batches`/
`notif_queue_batched()` mechanism (`reaction`/`comment_also`/`feed_activity` already use
it): it pools by (user, category), and this type shares category `community` with casual
social batched types - mixing "a member may be drifting away, a human should reach out"
into the same rolled-up digest as reaction counts would bury exactly the thing meant to
stand out. Built a narrower fix instead: per run, per recipient, count how many due flags
actually apply to *them* (after the self-exclusion fix from earlier today) - exactly one
gets today's specific per-flag wording and deep link, unchanged; more than one gets ONE
consolidated notification naming the count ("3 חברים עשויים להתרחק"), never N separate
pings. The everyday case (flags trickle in roughly one per day, matching the detection
job's own cadence) is untouched; only a genuine burst is affected. Also added
`serverTitle: true` to the client's `engagement_decline_flagged` entry - the server now
sends a genuinely different title for the single-vs-many case, and without that flag the
client's static string would have silently overridden it.

Caught one real bug while building this: the first draft tried `max(uuid)` to find a
representative `club_id` across several flags - Postgres has no such aggregate. Simplified
to `default_club_id()` directly, matching this schema's own established single-club
architecture rather than aggregating something that never varies anyway.

New pgTAP scenario proves the burst case directly: three simultaneous flags (including one
on the coach themselves, to exercise the count-per-recipient logic and the self-exclusion
rule at the same time) produce exactly one notification per recipient, with each
recipient's count independently correct (2 for the self-flagged coach, 3 for admin and
owner) - not nine separate pings.

Verified: `supabase test db` 95/95 files (3299 tests), `check-migration-immutability`
clean, full JS suite 1515/1515, full browser-check 35/35. Pushed to GitHub main and
applied to the live Supabase production project.

## Button/interaction consistency pass — 2026-09-10

Asked to check that every button/interactive element is polished and clean, app-wide.
Forked a systematic audit (not a general review - correctness/security have already
been covered exhaustively this session) across app.js, cloud.js, and index.html's shared
CSS: ad-hoc inline-styled buttons, missing icon-button labels, inconsistent busy/disabled
states, `:focus-visible` coverage gaps, tap-target sizing, and off-token colors. Two real
findings, one minor:

- **The Community search box had zero visible keyboard-focus state.** `.search-box input`
  sets `outline:none` (correct - the input is meant to look borderless inside its own
  decorated pill) with nothing compensating, silently breaking the one input in an
  otherwise-universal `:focus-visible` pattern. Added `.search-box:focus-within` on the
  container instead - highlights the whole pill, not the invisible input inside it.
- **Eight edit/delete icon buttons rendered ~23px tap targets** (log-entry, WOD-entry, and
  measurement edit/delete, app.js) - a raw `padding:4px` around a 15px SVG, never given
  the 44px floor the rest of the app converged on. The app already has a fix for this
  exact shape of problem (a transparent `::after` expanding the hit area without growing
  the visible element, used on the header's hamburger/bell) - deliberately NOT reused
  here: edit and delete sit right next to each other, and two overlapping invisible 44px
  boxes would make the one real risk (a tap meant for "edit" landing on "delete" instead)
  worse, not better. Grew the real box instead via a new shared `.icon-btn-sm` class,
  accepting a slightly taller row as the correct trade for a destructive control sitting
  this close to a non-destructive one. Checked visually before and after, both themes -
  clean spacing, no layout breakage.
- **Minor**: a "reset to today" date button's full inline style was byte-identical,
  copy-pasted between the Add and WOD tabs - promoted to a shared `.reset-date-btn` class
  so the next tweak to one actually reaches both.

Everything else checked out clean: icon-only buttons are all correctly labeled, busy/
disabled-state handling is appropriately differentiated (Community's real network calls
show it, app.js's local IndexedDB writes correctly don't need to), and off-token color
usage is limited to a handful of deliberate fixed-contrast badge colors, not accidental
theme breaks.

Verified: full JS suite 1515/1515, full browser-check 35/35 including `a11y-axe-scan.mjs`.

## A real privacy bug in this morning's engagement alerts, found by asking for a second opinion — 2026-09-10

Asked to do a full fresh research round across the whole app, reconciling against
everything shipped today. An independently-forked adversarial review (not a restatement
of my own earlier testing) found one real, confirmed bug in code already live on
production: `coach_notify_engagement_flags()` (this morning's own migration, 202609100002)
could notify a flagged member about their OWN engagement decline, if that member also
holds a coach/admin/owner role - realistic in a small gym, where the coach is often also
a training member. `coach_engagement_flags`' founding migration (202608280011) names this
exact outcome, in these words, as the one thing the whole feature must never produce; the
table's own RLS still held that line, but the new notify function opened a second channel
to the same information a push/in-app notification isn't covered by.

Fixed with a new migration (202609100003, `coach_notify_engagement_flags()` re-declared
whole - the earlier one is already applied and migration-immutable): one added predicate
excludes the flag's own subject from its own recipient loop. Checked production first -
zero open un-notified flags right now, so no real member was ever actually affected, but
the very next real decline in a coach's own attendance would have been. New pgTAP scenario
proves it: a flagged coach gets zero notifications about themselves while admin/owner still
get notified about the coach's decline.

Two smaller, real gaps closed alongside it, both flagged by the same research round:

- **The Boards tab badge (added this morning) didn't reach the desktop-sidebar nav-menu
  preview** - `getCommunityNavPreview()` is a hand-duplicated copy of the real tabs array
  by design (documented "must stay byte-identical" comment), and the badge computation was
  missing from the copy. A member on a 900px+ viewport saw no "challenges ending soon"
  signal until they actually clicked into Community. Mirrored the same computation into
  both places.
- **RISK_REGISTER.md's own "most concerning open item"** (AUDIT0827-OPS-H4/RESCAN-H5,
  claiming `purge_due_accounts()` was never scheduled) was itself stale - the document's
  own top-of-file addendum already flagged this as fixed and pointed at
  `CORRECTIONS_COMPLETED.md`, but the actual table rows still read STILL_OPEN. Confirmed
  the fix is genuinely live on production (`cron.job` query), marked both rows
  VERIFIED_FIXED, updated the summary counts.

Also reconciled: the doc trail's overall verdict is unchanged (CONDITIONAL, 91/100, blocked
only on the same external device-testing/branch-protection/secrets items every pass has
named) - nothing shipped today touches any of that.

Verified: `supabase test db` 95/95 files (3292 tests, new self-exclusion scenario in 0094),
`check-migration-immutability` clean, full JS suite 1515/1515 (1 new test proving the nav
preview badge), full browser-check 35/35. All three fixes pushed to GitHub main and applied
to the live Supabase production project (confirmed via `supabase migration list` - local
and remote now match exactly through 202609100003).

## Structural opportunities from the Community research pass, three of four shipped — 2026-09-10

A research pass on the Community tab's structure ("effective, easy, fun, and beneficial to
both members and owner") found the retention loop weak (every notification type is reactive
or administrative, nothing gives a member a reason to open the app on a rest day) and coach
tooling proactive but still pull-only (coach_engagement_flags is detected daily but never
pushed to a coach - they have to open the Coach tab to find out). Asked to build all four
ranked opportunities and add an admin off-switch for each.

**1. Boards tab badge.** The tab pill for challenges/leaderboard carried no ambient signal,
unlike Manage's own pendingReports badge two tabs over. Now badges with a count of active
challenges ending within 48h - the same window `chal_notify_ending_soon()` already uses
server-side, off data already loaded at boot (zero new fetches). Fixed a latent aria-label
bug in passing: the shared tab-badge markup hardcoded "X דיווחים ממתינים" for every badge on
that bar, which would have mis-described this one to a screen reader; generalized to a
`badgeLabel` field, defaulting to the original string so nothing else changes.

**2. Growth loop.** Turned out to already be built: `renderInviteQrPanel()`'s "שליחה לטלפון"
button already calls `navigator.share()` with the real invite link and QR image
(`shareInviteQr()`/`performInviteShare()`). Nothing to add. The bigger idea researched
alongside it - letting an ordinary member (not just coaches/admins) share an invite from
their own achievement posts - runs into two deliberate, tested boundaries on purpose: the
outward-share card's own Rule 2/3 explicitly forbid club identity or any URL ("an image that
has left this app has no RLS behind it any more"), and the `member` role holds no invite
permission today. Left alone rather than silently reversing either; flagged as a real,
separate product decision if the owner wants to revisit it.

**3. Streak-at-risk nudges** (`notif_streak_at_risk()`, new). Daily job: a member with a
3+ day activity streak (consecutive days the app was opened) who hasn't opened it yet today
gets an honest reminder. Deliberately NOT gated on leaderboard visibility - this is a private
reminder about a member's own number, not a board read. Self-limiting by construction (the
"last activity = yesterday" predicate matches at most one calendar day per at-risk episode),
so one daily cron run cannot double-notify without needing a tracking column.

**4. Engagement-decline alerts to staff** (`coach_notify_engagement_flags()`, new). The
existing daily detection job (`coach_detect_engagement_decline()`, already scheduled, never
touched) still only writes the flag. This fans a NEW flag out to every coach/admin
(`mod_alert_recipients()`, the same resolver `new_report` already uses) once - a new
`notified_at` column gates it, the same "notify once per thing" idiom
`challenges.ending_soon_notified_at` already established. Deliberately carries no member
name or handle: PRIVACY.md documents this signal as hidden from the member it is about, and
a push banner is a surface a coach's own notification centre doesn't otherwise expose to.

**The admin off-switch, as asked**: two new `club_features` toggles
(`streak_risk_nudges`, `engagement_alerts`), the same generic mechanism every other module
toggle already uses - no new table, no new RPC, genuinely server-enforced (checked inside
each new function itself, not just hidden client-side), on by default.

Verified: local `supabase test db` (95 files/3289 tests, a new `0094` file covering both
jobs' eligibility rules, idempotency, privacy, and the off-switch), `check-migration-
immutability` clean, full JS suite 1514/1514 (2 new + 2 pre-existing tests updated for the
new toggle/pref counts, with the updated numbers justified inline), full browser-check
35/35 including `a11y-axe-scan.mjs` and `community-render-cost.mjs`. One early false-alarm:
a first `supabase test db` run showed 5 unrelated files failing - traced to leftover
pollution from my own earlier ad-hoc manual test insert in the shared local dev database,
not a real regression; a clean `db reset` confirmed it.

## The Community feed "feels cheap" — a scoped polish pass, checked against the approved mockup — 2026-09-10

Reported directly. Compared the current feed markup/CSS against the already-approved
Direction 06 reference design (`mockups/06-community.png`) instead of guessing at a new
direction, then forked a second, deeper research pass on top of the first fix to find
anything still worth doing. Five real, low-risk gaps, all CSS/markup-only - no new
data, no new fetches, no schema/RLS touched:

- **The composer entry point read as a utility button**, same weight as "טעינת עוד"
  below the feed - easy to miss as the one thing on the screen that starts something.
  Now the standard "fake input row" every social feed uses for the same tap target:
  the member's own avatar + a greyed "מה קורה היום?" placeholder, full width. Same
  `data-community-action="open-composer"`, so every existing composer test still
  targets the same element.
- **The announcement card was indistinguishable from any other card** except a badge
  string and an emoji typed into the title. Now a visibly separate voice in the feed -
  a warm brass-tinted card background plus a 📣 icon badge replacing the generic "ח"
  club mark every other authorless post type still shares. Contrast computed against
  the actual tinted background, not the untinted surface, before shipping: 5.13:1
  light / 6.19:1 dark.
- **The reaction/comment row was two identical grey chip buttons** - a reaction and a
  comment count looked exactly like any filter chip or subtab elsewhere in the app.
  Cheer now gets the same filled warm-pill treatment `.pick-hero-cta` already
  established for a primary CTA (--energy-text on an 8% tint: 5.41:1 light / 4.83:1
  dark, computed, not assumed); comments stays a plain, quieter icon+count since it
  opens a thread rather than registering a reaction.
- **PR/achievement/attendance-milestone, challenge, and event cards had no visual
  weight of their own** - a thin colored top accent instead of a repainted card
  (brass for PR/achievement/milestone, teal for challenges, blue for events - the
  same hues `sectionHead()` already uses for those categories elsewhere).
- **Feed head avatars were 36px**, a touch small against the mockup's heavier avatar
  weight - bumped to 40px at the one call site that's actually the main feed card
  head, not a blanket change to every 36px avatar in the app (comments, directory
  rows keep their own deliberate sizing).

Verified: the exact `community-render-cost.mjs` frame-budget trip-wire this touches
directly (the feed's own hot path) still passes with margin - 5ms at 4x CPU throttle
against a 16ms budget. Full suite 1512/1512, full browser-check 35/35 including
`a11y-axe-scan.mjs` and `community-post-composition.mjs` (the composer flow itself).
Checked visually in a real Chromium page, both themes, before calling it done - not
just by CSS reasoning.

**Flagged, not implemented - product decisions, not styling:** the mockup's
weekly-leaderboard preview card sits inside the feed itself; today it's a fully
separate "Boards" sub-tab with its own, already-reasonable styling. Folding a
leaderboard preview into the feed is real work (a new render path, plus confirming
the data is even loaded while the Feed sub-tab is active) - a scope call for the
owner, not something to bundle into a CSS pass. Feed personalization/ranking
(`docs/audit/FEATURE_RECOMMENDATIONS.md` FEAT-010) is a longer-term, separate-track
item that also contributes to a feed reading as generic over time, independent of
card styling.

## Closed the one real onboarding gap: what becomes visible when you join — 2026-09-10

A full end-to-end audit (every screen, every feature, prepared for board review) gave
onboarding a skeptical re-look after repeated concern that the earlier "already fine"
verdict wasn't the full story. It wasn't: `RISK_REGISTER.md`'s AUDIT0827-PROD-3, open
since 2026-08-27, was real and never closed — nothing in the sign-up flow tells a new
member what happens to their data once they join Community.

Checked `PRIVACY.md`'s actual documented defaults before writing a word of copy, rather
than guessing: profile visibility is ON by default, but workout results, PRs, and
attendance are all OFF by default and only publish when a member chooses to share them.
So the honest sentence is "your profile is visible, your numbers are not, until you say
so" - not the more alarming "everything becomes public" a first guess might have shipped.

Added one sentence to the intro carousel's existing `club_rules` step (the step already
covering club policy facts - hours, dress code, cancellations), via a new migration
(`202609100001_intro_carousel_data_visibility_disclosure.sql`) rather than a fourth
carousel screen: the table's own CHECK constraint fixes the step set at exactly three,
so a new screen would have been schema surgery for a one-sentence gap. The UPDATE is
guarded to only touch the row if its body still matches the original seed text
byte-for-byte, so a club that already customized this step through the admin content
editor keeps its own words.

Verified locally: `supabase test db` (94 files / 3265 tests, including the exact row
after a full `db reset`), `check-migration-immutability` clean (new file, nothing
edited), full JS suite 1512/1512, `community-intro-carousel.test.mjs` +
`first-run-sequence.test.mjs` 35/35 (JSDOM fixtures, unaffected by the DB seed change
as expected). `RISK_REGISTER.md`'s AUDIT0827-PROD-3 row and its summary counts updated
to VERIFIED_FIXED.

While assembling the audit, one other reported finding turned out to be a false
positive from stale documentation, not a real gap: the "any coach can edit any
admin's announcement" claim (SEC-010) cited a 2026-08-27 policy that a 2026-09-06
migration had already superseded - `announcements_update_admin` has been
author-or-admin, with cross-author edits audited, for four days. A passing pgTAP test
(`0079_product_decisions_attendance_and_announcements_test.sql`) already proves it.
Corrected before it reached the board report, not after.

## Re-audited the three just-fixed screens — 2026-09-10

Asked to re-audit after the previous fix. Forked one pass over the same
three areas (Calendar, Progress's body-measurements section, Add tab)
to check the fixes themselves and look for anything left. Two of three
fixes were clean; the third left one harmless dead ternary from the
refactor - `renderLogTab()`'s ladder/superset panel had
`${ladderMode ? \`...\` : ""}` wrapping the round-detail block, but by
that point in the function `ladderMode` is always `true` (the inactive
case already returned earlier). Collapsed to a plain template literal;
no behavior change, since the `: ""` branch could never have run.
Nothing else in the three areas cleared the bar.

`test/bodyweight-measurements.test.mjs`, `duration-entries.test.mjs`,
`superset-blocks.test.mjs`, `clear-data.test.mjs`, `app-flow.test.mjs`
(43/43), full suite (1512/1512), full browser-check (35/35) all pass.

## Three real gaps from a full member-facing UX sweep — 2026-09-10

Asked to run the same "more complicated than it needs to be" audit across
every member-facing screen, not just admin/Community. Forked four
parallel audits (Add/WOD, History/Progress + Calendar, Community's
social side, onboarding + Settings). Three came back clean on inspection
- Community, onboarding, and Settings had all already been through
deliberate simplification passes and nothing new cleared the bar. Three
concrete fixes landed:

- **Calendar tab showed the wrong title.** Tap "לוח שנה" in the bottom
  nav, land on a screen whose h1 said "היסטוריה" - a straight mislabel
  (the History/Progress tab, internally called `history`, correctly
  shows "התקדמות"; only Calendar's own title had drifted from its nav
  label). `app.js:4210`, one line.
- **Progress tab's "add new measurement" outranked the measurements you
  already track.** `renderMeasureArea()` rendered a bold, brass-bordered
  "+ הוספת מדד חדש" CTA first, above every existing measurement - the
  rare once-per-type action beating the thing you actually do every
  visit (log today's value into a type you already have). Moved the
  control after the real rows and dropped it to plain-row weight
  (`.link-btn`, no border/CTA styling) - same control, same
  `data-action="open-add-measure-type"`, just no longer first in line.
- **Add tab's ladder/superset toggle competed with the actual set
  entry.** Every single log session showed a full-width, two-line,
  icon'd CTA for structured ladder/superset logging directly under the
  weight/reps/sets steppers - a feature most single-set sessions never
  touch. Shrunk the inactive state to a small `.link-btn`; the full
  control (live round count, block-label chips, partner exercise, the
  whole panel) still renders at its original weight the moment it's
  actually active - nothing about the feature itself changed, only how
  loud it is before you've asked for it.

No ids, `data-action`s, or test selectors touched - confirmed against
`test/bodyweight-measurements.test.mjs`, `test/duration-entries.test.mjs`,
`test/superset-blocks.test.mjs`, `test/clear-data.test.mjs`, and
`test/app-flow.test.mjs` before editing (all check for the active-state
"...פעיל..." text via `[data-action='toggle-ladder-mode']`, none assert
on inactive-state markup or DOM order). Full suite (1512/1512) and the
full browser-check run (35/35, including `ladder.mjs`, `superset.mjs`,
`roadmap.mjs`) both pass unchanged.

Left alone: an unrelated, already-in-progress edit found in the same
file mid-session (the WOD benchmarks subtab label "Benchmarks"→"קטלוג")
- not something this pass touched, staged separately with `git add -p`
so it ships on its own.

## Same fix, second surface: Member of the Week's coach's-pick form — 2026-09-10

Follow-up to the invite-flow simplification below - a fork audited the
rest of the Community/admin surfaces for the same "more complicated than
it needs to be" pattern and found one clean match: the coach dashboard's
Member of the Week section. Whenever computed candidates exist,
`renderCoachMemberOfWeekSection()` rendered the candidate list AND a
full always-open "coach's pick" form (username, reason textarea, submit)
directly beneath it - a free-text manual override sitting in equal
visual weight next to the one-tap "פרסום" button on each actual
candidate, for what COMM-315 itself treats as a fallback path.

Checked `test/community-member-of-week.test.mjs` first: every assertion
on the populated-candidates case uses `querySelector('[data-mow-pick-*]')`
presence, not visibility, so the same `<details>` disclosure already
used for the invite flow's shared-code panel applies here unchanged -
the form stays in the DOM with the same ids/data-actions, now tucked
behind a "בחירה ידנית של חבר/ת השבוע" summary instead of always-open.
Left it open in every OTHER branch (empty candidates, free_selection,
coachs_pick) - there it's the only action on screen, so collapsing it
would just add a click with nothing to hide it from.

`test/community-member-of-week.test.mjs` (14/14) and the full suite
(1512/1512) both pass unchanged.

## Simplified inviting a member; two real contrast bugs found along the way — 2026-09-10

Reported directly: inviting one member was "way more complicated than it
needs to be." Read the actual code before proposing anything - the
"הוספת חבר/ה" (Add Member) tab stacked three systems: a QR panel
rendered ABOVE everything (its own empty state explains itself before
either form below it has created anything), and two full forms side by
side under one combined header - a personal invite (the common case: one
named person) and a shared/bulk join code (a genuinely rarer case, meant
for a printable front-desk flyer). A coach just wanting to invite the
person standing in front of them had to first work out which of two
forms was the right one.

**Nothing about what these do, or who can see them, changed** - checked
against `test/community-invite-code-management.test.mjs`,
`community-invite-qr.test.mjs`, and
`scripts/browser-check/community-person-invite-lifecycle.mjs` before
writing anything, not after: every form id (`#communityInviteCodeCreate`,
`#communityInviteCreate`), field name, `data-action`, and
`data-*-panel`/`data-*-section` marker those tests assert on is
byte-identical. What changed is order and default visibility:
`renderInviteManagement()` now puts the personal-invite panel first,
retitled from "ניהול הזמנות וקודי הצטרפות" to "הזמנת חבר/ה" (the section
itself, not a new one - see the test-file comment explaining exactly
that), with the shared/bulk-code panel moved into a `<details>`
disclosure ("עוד אפשרות: קוד הצטרפות משותף...") - present in the DOM
exactly as before (the unit tests `dispatchEvent`/`requestSubmit()`
directly on it, which doesn't care about open/closed state) but not
competing for the first glance. The QR panel and incomplete-signups
tracker now render AFTER the invite form instead of before it, so the
form - the actual action - is what a coach sees and can act on
immediately.

**Two real, pre-existing WCAG failures found while axe-checking the
restructured tab**, both the same `--token-as-text` class of bug fixed
several times earlier this session: `.admin-tag` (the "ניהול" pill on
every `sectionHead()` across the app, not just invites) used
`color:var(--energy)` - a fill/border-safe token, never text-safe -
switched to `--energy-text`. `.chip-btn.selected` used `--brass` at
4.35:1 against `--surface2` (`#E9EFF8`), just under AA - the token's own
comment already documented one earlier darkening pass that verified it
against `--surface`/`--bg` but never happened to check `--surface2`.
Darkened again, `#956529` → `#8a5d25` (4.95:1 on `--surface2`, 5.72:1 on
`--surface` - darkening only ever helps against something lighter, so
every other pairing improved too, not just the one that was failing).

A regression-guard test (`community-manage-tab.test.mjs`, "every section
the seven-tab Manage rendered is still reachable") legitimately needed
updating - it hardcoded the old section heading text as a marker; updated
to the new heading with a comment explaining it's the same section, not
proof of a silently orphaned one.

Verified: `npm test` 1512/1512, `run-all.mjs` 35/35, `a11y-axe-scan.mjs`
clean, a targeted axe pass on the invite tab specifically (both themes,
disclosure open and closed - 4 checks, all previously failing on
`.admin-tag`/`.selected`, now clean), confirmed via DOM query that the
shared-code form exists before the disclosure is opened and becomes
visible after. `APP_VERSION` bumped to `4.16.0` (a real feature/UX
change, not a patch-level fix).

## The 4-stat summary row is deleted, not conditional — 2026-09-10

The previous pass made it show only when `hasLoggedToday` - reported
back directly: "The circled in red still there, I don't want it at all.
Remove delete." Making it conditional was the wrong level of fix; removed
the block entirely from `renderLogTab()` instead, regardless of state.
Also removed what it leaves behind rather than leaving it half-cleaned:
`dayExerciseCount`/`dayVolume`/`dayDurationMin`/`dayPRCount` (computed
only to feed the row, now unused) and the three
`.scene-page--add .stat-row[aria-label]` CSS rules (including the
`max-width:320px` narrow-phone override) that styled markup which no
longer exists.

Verified: `npm test` 1512/1512, `run-all.mjs` 35/35, `a11y-axe-scan.mjs`
clean, confirmed via DOM query that `.stat-row[aria-label]` is absent
both before AND after logging a set (the previous pass's conditional
only checked the "before" case). `APP_VERSION` bumped to `4.15.9`.

## Fifth jump report was a real, different bug — plus a corrected fix and two more from a marked-up screenshot — 2026-09-10

**The actual "box jumps" cause.** Not a page-scroll issue at all this time
- reported precisely: "it's the box where you can put your exercise that
jumps." `.scene-sheet{ animation:scene-sheet-in .2s ease-out; }` (gated
behind `prefers-reduced-motion:no-preference`, so it wasn't a motion-
accessibility bug) was meant to play once, entering a scene tab. It
actually replayed on every single re-render *within* the tab -
`render()` rebuilds `#content`'s innerHTML wholesale on nearly every
interaction (typing a weight, tapping a stepper, anything), so the
browser saw a "new" `.scene-sheet` matching the selector each time and
restarted the 12px-translateY + fade from scratch. No state exists today
to distinguish "just switched into this tab" from "re-rendered within
it," so removed rather than half-fixed.

**A wrong turn, corrected the same session.** Also reported (with a
screenshot circled in red): a warm/reddish tint still visible behind the
stat cards, after the ambient photo layer was already removed. First
guess wrong: assumed it was the scrim's own added coral radial-gradient
and removed that - genuinely a real contributor, correctly removed. But
then also raised the sheet's opacity from `.8` to `.95` to kill the
*remaining* bleed (the backdrop-filter blur sampling the actual red-
striped photo through the translucent sheet, inherent to glass sitting
near a colorful photo) - which was NOT wanted. Corrected immediately:
"I liked the transparency" - reverted to `.8`. The circled screenshot
turned out to mean something narrower than either guess: remove the
4-stat summary row itself, not reduce transparency anywhere. Recorded
here as a real example of two guesses in a row on ambiguous visual
feedback, corrected in full as soon as the actual intent was clarified,
rather than left half-applied.

**The 4-stat summary row (תרגילים/ק"ג נפח/דק'/שיאים חדשים) is
conditional again.** It used to be gated on `hasLoggedToday` (the same
flag the completion checkmark already uses) before the reference-
accuracy pass made it unconditional - showing four zero/dash cards
before a member has logged anything today was exactly the clutter the
circled screenshot was pointing at. Restored: `${hasLoggedToday ? ... :
""}`.

**"עבודה מעולה!" (great job!) is conditional too, for the same reason.**
Reported directly: it shouldn't show all the time, only right after
logging something, then disappear again. It had the identical
unconditional-regression as the stat row - restored to the same
`hasLoggedToday` check the title's completion badge already uses, with
"מוכנים להתחיל?" (ready to start?) as the before-logging state, matching
this session's very first pass at this screen (which had exactly this
conditional, lost somewhere in a later rewrite).

Verified together: `npm test` 1512/1512, `run-all.mjs` 35/35,
`a11y-axe-scan.mjs` clean, every state change (subtitle text, stat-row
presence, sheet opacity) confirmed via computed DOM content in headless
Chromium before and after logging a set, not just visually. `APP_VERSION`
bumped again to `4.15.8` and re-synced - see the entry directly below for
why that step is not optional on any pass that touches production code.

**The real reason nothing looked updated: APP_VERSION never moved.**

Reported directly: "Didn't see any update on app. And screen still jumps."
Investigated rather than assumed - `git log -p` on `app.js` shows
`APP_VERSION` was bumped to `4.15.1` at the reference-accuracy-pass commit
and then **never bumped again** across the five real fix commits that
shipped after it (the nav-jump fix, the full Navy Stripe ship, light
theme, extending it to all five screens, and both jump-investigation
fixes). `sw.js`'s own comment states the mechanism plainly: "bumping
APP_VERSION in app.js is what ships an update" - the service worker has
no other signal that a new version exists. Every fix in this file below
was correct in the repository the whole time; none of them had a way to
reach an already-installed client, because the cache-busting version
identifier stayed frozen at 4.15.1 through all of it.

Bumped to `4.15.7` (one per real change since 4.15.1) and re-synced
`SW_VERSION` via `npm run sync-version`. Verified `npm run check-version`
passes.

## Three real fixes from a live screenshot, once actually visible — 2026-09-10

**1. Progress screen no longer auto-expands an exercise on load.**
`renderHistoryListArea()` unconditionally rendered
`renderDetailCard(active[0])` - the first exercise's full chart - open
before any tap, whenever nothing was explicitly selected. Reported
directly ("progress should be open only when the user is pressing an
exercise"). Removed; every row now starts collapsed, matching the
`historyId === m.id` condition every other row already used. Verified: 0
charts render on load, tapping a row still opens exactly that one.

**2. Progress chart no longer plots one point per SET.**
`renderDetailCard`/`renderDurationDetailCard` fed `renderChart` one data
point per logged entry - several sets in one session landed as several
points on the exact same date (the reported screenshots showed "10.09"
repeated three times and "27.08" repeated six). Researched rather than
guessed at the right behavior: every mainstream strength-tracking app
that plots 1RM-over-time (Strong, Hevy, ...) shows one point per session
day, the best set of that day - a progress chart tracks day-to-day
change, and multiple sets in one session are reps of the same workout,
not separate progress. Added `bestPerDay(entries, valueOf)`, used by
both chart builders; the RM-table/bestEst1RM/repRecordFor were already
correct (a global max across all sets is unaffected by how many sets
happened on any one day) and are untouched. Verified: three same-day sets
at 80/90/100kg now render exactly one chart point (100kg, the best).

**3. Exercise rows in the day-entries list no longer wrap mid-row.**
`.scene-page--add .log-row > .flex{flex-wrap:wrap;}` forced wrapping with
no truncation fallback - reported directly with a screenshot showing the
edit/delete icons and exercise name landing on two misaligned lines.
Classic flexbox gap: flex items default to a content-based minimum width,
so once a row's total content exceeded the available width, wrapping was
the only way the browser could fit it. Removed the forced wrap; both
flex halves now get `min-width:0` (so they can actually shrink) and the
exercise name gets real `text-overflow:ellipsis` truncation instead, so
a long name shortens with "…" and the 44px edit/delete targets never
lose their size to make room. Verified: three logged sets render three
uniform 56px-tall single-line rows.

Verified together: `npm test` 1512/1512, `run-all.mjs` 35/35,
`a11y-axe-scan.mjs` clean, `npm run check-version` passes.

## Fourth jump report — a dvh instance that survived the original fix — 2026-09-10

Reported specifically as jumping "getting in the app" (app launch), not a
tab switch this time - a real, different instance of the same underlying
class of bug. `#loading` (index.html) - the screen actually on-screen
during that exact moment - still used `min-height:100dvh`, missed by the
original dvh->svh sweep because it isn't a `.scene-page`. Fixed the same
way: `100svh`. Also converted `#welcomeOverlay .welcome-scene` and
`#achievementsOverlay .modal-sheet` (both `100dvh`) for the same reason -
both are shown during/near the same "entering the app" window (first-run
and, for achievements, a modal reachable from very early in a session).
Left the desktop-only context-column `max-height:calc(100dvh - 56px)`
alone - desktop browsers don't collapse an address bar on scroll, so it
isn't the same failure mode, and changing it isn't free (a different
intended behavior around the 56px offset).

Also removed the "אימון כוח"/"אימון שהושלם" label from the Add screen's
date row (`.scene-summary-meta`), per direct request - the row now shows
just the date.

Verified: `npm test` 1512/1512, `run-all.mjs` 35/35, `a11y-axe-scan.mjs`
clean, confirmed via computed text content that the label is gone and
only the date remains.

## Removed the ambient photo layer, per direct request — 2026-09-10

`.scene-page__ambient` (the heavily blurred, dimmed copy of each scene's
photo sitting behind the whole glass sheet) is gone - the div from all
five render paths (`renderLogTab`/`renderCalendarTab`/`renderHistoryTab`/
`renderWodTab` in app.js, the Community scene in cloud.js) and its CSS
rule, including the `position:fixed` fix from the entry above (moot once
the element itself is gone). Everything else Navy Stripe added stays:
the stripe ribbon, the lighter scrim, the glass sheet and glass CTA. The
sheet's own translucency still reads as glass - it now shows a plain
blurred navy/cream instead of a blurred photo behind it, which is a
perfectly normal frosted-glass look on its own.

Verified: `npm test` 1512/1512, `run-all.mjs` 35/35, `a11y-axe-scan.mjs`
clean, confirmed via computed styles that `.scene-page__ambient` no
longer exists in the DOM on any of the five screens.

## Third jump report — the ambient layer's fixed background, not dvh — 2026-09-09

Reported again ("the page still jumping") immediately after Navy Stripe
shipped to all five screens. The original dvh→svh fix (still correct,
still in place, confirmed no dvh remains on anything in the tab-switch
path) wasn't the culprit this time. Root cause: `.scene-page__ambient`
used `position:absolute` + `background-attachment:fixed` to size
`background-size:cover` against the viewport instead of its own very-tall
(full page content height) box. `background-attachment:fixed` on a tall
scrolling element with a heavy `filter:blur(46px)` on top is a well-known,
severe mobile scroll-performance anti-pattern - most engines can't
cheaply composite it, since the browser has to reconsider the blurred
background's position against the scrolled box on every frame rather
than treating it as a static layer. This existed on Add alone since the
first Navy Stripe ship; extending it to all five screens turned an
existing-but-easy-to-miss cost into something impossible to miss.

Fixed the right way: `position:fixed` on the ambient ELEMENT itself
(matching how `.header`/the dock chips already work), not a fixed
background on an absolutely-positioned element. A small, viewport-sized
fixed layer is cheap for the compositor to treat as static; a huge
scrolling element with a fixed-attachment background is the expensive
version of the same idea. Confirmed `isolation:isolate` on `.scene-page`
(its ancestor) does NOT turn it into a containing block for
`position:fixed` descendants - only transform/filter/perspective/contain
do, and `.scene-page` sets none of them - so the layer still resolves
against the real viewport, verified via `getBoundingClientRect()` before
and after a scroll (identical position, as intended) rather than assumed
from the spec text.

**Honesty about verification limits**: headless Chromium's own
`layout-shift` PerformanceObserver shows negligible CLS (~0.001) both
before and after this fix - consistent with the whole project's earlier
finding that this class of jank is a real-device GPU/compositor cost,
not a layout reflow this sandbox can directly measure or reproduce. The
fix is the standard, well-documented correction for the anti-pattern
found; it has not been confirmed to eliminate the felt jank on an actual
phone, because nothing in this environment can test that.

Verified: `npm test` 1512/1512, `run-all.mjs` 35/35, `a11y-axe-scan.mjs`
clean, ambient layer's position confirmed static across scroll via
computed `getBoundingClientRect()`.

## "Navy Stripe" extended to every scene screen — 2026-09-09

Extended from Add-only to Calendar, Progress, Library and Community
(app.js's `renderCalendarTab`/`renderHistoryTab`/`renderWodTab`, and
cloud.js's Community scene) — both themes, all four. Kept: Add's own taller
`--scene-photo-height` (that was tuned specifically against its own
mockup pass; the other four screens' existing, separately-approved
VISUAL_QA_PROTOCOL.md proportions are untouched). Not extended: the glass
CTA treatment, since only Add has one dominant primary action - the other
screens don't have an equivalent element to apply it to.

**Generalized, not duplicated, using what the scenes already share**:
- `.scene-page__ambient` now reads `var(--scene-image)`/
  `var(--scene-position, center top)` - the same custom properties each
  `.scene-page--*` class already sets for its own `.scene-page__media` -
  instead of a second per-screen hardcoded URL. One rule, every screen
  automatically gets its own photo.
- The lighter scrim (previously Add-only) turned out to be a defect on
  every scene, not just Add - they all shared the one original catch-all
  scrim rule, so all of them were darkening to .62 opacity by the
  halfway point.
- The glass sheet (light .88 opacity / dark .8, both measured for
  contrast, not eyeballed) extends the same way - the underlying question
  was never Add-specific ("does translucent coral/navy/cream work under
  nested opaque cards"), so the same verified values apply everywhere.

**A real specificity bug caught while generalizing, before it shipped**:
the naive generalized selector `.scene-page > .scene-page__scrim` computes
to specificity (0,2,0) - weaker than the existing
`:root[data-theme="dark"] .scene-page__scrim` rule already in this file at
(0,3,0). Without noticing, the lighter-scrim fix would have silently lost
in dark theme specifically - the exact theme it was reported against -
while appearing to work in light theme, where the competing rule doesn't
match. Fixed by adding `body[data-scene]` to the selector
(specificity 0,3,1), computed and verified via getComputedStyle in a real
browser, not assumed from source order.

Verified: `npm test` 1512/1512, `run-all.mjs` 35/35, `desktop-layout.mjs`
clean, axe clean across all 5 scene screens in both light and dark (10
checks total), computed styles (sheet background/blur, ambient's
background-image resolving to each screen's own photo, scrim gradient)
confirmed per-screen via headless Chromium rather than assumed from the
Add-screen result alone.

## "Navy Stripe" extended to light theme — Add screen — 2026-09-09

The dark-theme ship below stayed dark-only deliberately, since that's all
that had been reviewed. Extended now: computed light-theme contrast
properly rather than reusing the dark values with a color swap, because
the two grounds behave oppositely. On the dark navy sheet, translucent
coral at .68 opacity measured ~3.9:1 for dark text vs. ~4.6:1 for light
text (light wins). On the light cream sheet, the same idea at .75 opacity
measured ~8.7:1 for dark text vs. ~2.2:1 for light text (white fails
outright) - so light theme keeps this app's existing dark-text-on-energy
convention (`#1a0d08`), not a copy of dark theme's light text. The sheet
itself got its own light-appropriate opacity too (.88, not dark's .8 - a
light ground reads translucency very differently, checked against real
rendered pixels rather than assumed safe because dark already passed).
Both new rules are unguarded (this file's established convention: light
is the default, dark is the guarded override), and were checked to still
have HIGHER specificity than the pre-existing unguarded rules they
replace, not just rely on coming later in the file.

Verified: `npm test` 1512/1512, `run-all.mjs` 35/35, axe clean on Add in
light theme both with and without a movement selected (the CTA's two
states), computed styles (background/backdrop-filter/color, not just a
screenshot) confirmed via headless Chromium.

## "Navy Stripe" direction — Add screen, dark theme only — 2026-09-09

Implemented after an interactive mockup exploration (six distinct future-
facing directions, then two rounds of refinement on the one chosen —
"combine Aurora Glass and HUD," then "make it the real navy/coral/
red-white-stripe identity from a live screenshot, not a foreign palette")
converged on: the actual live app's own colors and the red/white stripe as
a real UI ribbon (not just photo content), with glass depth and motion
borrowed from the other studies. Scoped to Add
(`.scene-page--add`/`body[data-scene="scene-page--add"]`) and **dark theme
only** — the whole exploration was reviewed against a dark-theme
screenshot and dark-theme mockups; light theme keeps its existing
`--club-paper` treatment unchanged rather than shipping an unreviewed
light-glass guess. Calendar/Progress/Library/Community were never part of
this exploration and are untouched.

**index.html**: taller photo (`--scene-photo-height` on `.scene-page--add`,
`clamp(360px, 56svh, 500px)` vs. the shared default), and a lighter scrim
that only comes up to real darkness in the last ~15% — the original scrim
darkened to .62 opacity by the halfway point, which is what made an
earlier mockup pass of this same photo read as "almost not visible" even
after doubling its height. A new `.scene-page__ambient` layer (heavily
blurred, dimmed copy of the same photo, `background-attachment:fixed` so
`background-size:cover` sizes against the viewport rather than the very
tall content box — the same zoom bug fixed earlier this project for the
sharp photo layer would otherwise reappear here) sits behind the *entire*
scrollable sheet, not just the photo band, so cards further down the page
have something real behind them instead of flat navy — reported directly
("why put transparency on cards if there's nothing behind them"). The
sheet itself and the primary save button (`#bottomBarBtn`) are both real
frosted glass now (measured contrast, not eyeballed — the CTA's text
flipped from dark to light because dark text on the translucent coral
measured ~3.9:1, light text ~4.6:1). A new `.stripe-ribbon` element (the
red/white stripe as an actual rounded UI ribbon, not photo content) sits
at the top of the sheet.

Selectors are deliberately over-specific
(`body[data-scene="scene-page--add"] .scene-page--add > .scene-sheet`,
not just `.scene-sheet`) because several earlier passes already left
multiple `.scene-sheet`/`#bottomBar .save-btn` rules at tied specificity
scattered through this file — matching or exceeding that specificity is
what actually guarantees these rules win, not just source order.

**app.js** (`renderLogTab`): added the `.scene-page__ambient` div and the
`.stripe-ribbon` div to the real markup.

**Regression found and fixed during this pass**: the stripe ribbon's first
sizing (8px + 16px margin) pushed `first-run-sequence.mjs`'s onboarding
tour card 7px below the fold on a 390×844 screen. Sized the ribbon down
(6px + 10px margin) rather than touching the test or the tour card's own
spacing, since the ribbon was the new element on the screen.

Verified: `npm test` 1512/1512, `run-all.mjs` 35/35, targeted axe passes
(both themes, with and without a movement selected — the CTA's two visual
states) all clean, computed styles confirmed via headless Chromium (sheet
background/blur, CTA gradient/color, ambient layer's background-image) in
both themes, not just visually eyeballed.

## Two bugs from live use, found after the reference-accuracy pass — 2026-09-09

**1. The screen visibly "vibrated" on every tab switch.** Root cause was
`100dvh` (dynamic viewport height) on `.scene-sheet` and `body` — the
switch-tab handler resets scroll to the top on every switch, and on a real
mobile browser, scrolling to the top is exactly the gesture that re-expands
a collapsed address bar. `dvh` tracks that address-bar animation frame by
frame, so anything sized against it visibly resized in real time for the
~200-300ms the browser chrome took to animate. Confirmed no abnormal
`layout-shift` entries in headless Chromium first (it has no browser chrome
to animate, so it can't reproduce this by itself) before concluding it was
a real, mobile-only reflow rather than a perception issue. Fixed: both
rules now use `svh` (viewport at its smallest, chrome fully expanded),
which does not change as the chrome animates.

**2. "Management and practice [workouts] are hidden in the hamburger."**
The reference-accuracy pass had demoted the WOD/Library tab's `main` flag
to `false` to match `design-reference.jpg`'s literal 4-icon bottom nav —
directly contradicting a comment three lines above it in `getNavItems()`
explaining, in detail, why that tab specifically belongs in the bottom bar
("has its own sub-nav" was already established as not disqualifying). The
Manage tab (staff-only) had the same problem from the other direction: its
own comment said "same footing as the other 5 (main: true)" while the code
next to it said `main: false`. Both restored to `main: true` — WOD is back
on the 5-tab bar, and staff/coach/admin accounts now get a 6th bottom-bar
icon for Manage instead of finding it only through the hamburger. `.tabbtn`
has no hardcoded child count (`flex:1`), so the 6th icon costs ~16.7% width
each rather than 20%, confirmed at 60px per icon on a 390px screen (well
above the 44px touch-target floor).

Re-verified after both fixes: `npm test` 1512/1512, `run-all.mjs` 35/35.

# Immersive club redesign — audit and implementation log — 2026-09-08

Handoff: `haimunia-immersive-full-claude-handoff/haimunia-claude-handoff/`
(`CLAUDE.md`, `IMPLEMENTATION_SPEC.md`, `SCREEN_ACCEPTANCE.md`,
`VISUAL_QA_PROTOCOL.md`, `PHOTO_MAP.md`, `design-reference.jpg`). This
supersedes the "Direction 06 / Club Balance" contained-photo-card pass shipped
earlier the same day (v4.15.0) on the primary scene pages — full-bleed photo
backgrounds replace the small `.photo-header` card on Add, History, Calendar,
Progress, WOD/Library, Community, and Achievements. `.photo-header` itself is
left in place (Settings, onboarding, and the modal-header cases that never
matched the immersive brief still use it) rather than deleted sight unseen.

## Audit (required implementation order, step 1)

**Render architecture**: `app.js`'s `render()` (app.js:4529) is the single
dispatcher — `tab` selects `renderLogTab()` / `renderHistoryTab()` /
`renderCalendarTab()` / `renderWodTab()` / `renderManageApp()` /
`renderCommunityApp()`, writes the result into `#content`, which sits inside
`<main>`, below a **persistent** `.header` (index.html:1432-1451, outside
`#content`, rendered once) and `.brand-stripe`. This is the one real
architectural wrinkle against the spec's `.scene-page__media{position:absolute;
inset:0}` sample: that sample assumes the media layer's containing block is
the per-page wrapper, but the header/brand-stripe live *outside* that wrapper
and currently take normal document flow space above it. Resolution: `render()`
now stamps `#app[data-scene]` per tab (from a new `PAGE_SCENES` registry), and
`.header`/`.brand-stripe` read that attribute to switch to a transparent,
absolutely-positioned overlay only on scene pages — the photo layer extends
under them instead of starting below them. Full reasoning in the CSS comments
at the token block.

**Bottom navigation — the one genuine spec conflict, resolved, not asked
about.** `IMPLEMENTATION_SPEC.md`/`SCREEN_ACCEPTANCE.md` require exactly four
primary destinations in the bar; the shipped bar (`renderBottomTabBar()`,
`#bottomTabBar`) renders five (`#tabAddBtn`/`#tabHistoryBtn`/`#tabCalendarBtn`/
`#tabWodBtn`/`#tabCommunityBtn`), and dozens of existing tests and
browser-check scenarios click those five ids by name (`switchTab(page,
"tabWodBtn")` etc. — the mobile nav-menu's own copy of these rows
*deliberately omits* the id to avoid a duplicate, per app.js:1425-1428's own
comment, so `#tabWodBtn` exists nowhere else in the DOM). Removing WOD's
button from the bar to hit "four" would either delete a non-negotiable,
test-covered id or leave it `display:none` — which fails the same tests
(`page.click()` requires a visible element). CLAUDE.md's own "Non-negotiable
engineering constraints" section ranks "preserve all existing IDs... do not
remove or rename working tests" above the visual composition requirements.
**Decision: keep all five destinations, ids and dispatch unchanged, restyled
in the dark/grounded/coral-active immersive language the spec asks for.**
Logged here per `IMPLEMENTATION_SPEC.md` §14's own request for "a short list
of deliberate differences from `design-reference.jpg` and the reason for
each" — this is that list's first and main entry.

**Screen-key mapping** (the reference's four bottom icons, mapped onto the
app's real tab ids, confirmed against actual current labels, not guessed):
`אימון`→`tab==="add"`, `היסטוריה`→`tab==="calendar"` (already the tab that
renders a month calendar + selected-day list — the reference's "History"
screen composition, not the raw-list one), `התקדמות`→`tab==="history"`
(already labeled "התקדמות" and already the PR/progress-chart screen — see
`app.js:114-118`), `קהילה`→`tab==="community"`. `tab==="wod"` (WOD/Library) is
the fifth, kept in the bar per the decision above, and is also the screen
`PHOTO_MAP.md`/`SCREEN_ACCEPTANCE.md` call "Workout library."

**Assets**: the 7 files in `assets/club-photos/*` are copied from the
handoff's own aliased folder (same source photography as today's earlier
Direction 06 pass — byte-identical originals, confirmed by size before
resizing), filenames unchanged per `PHOTO_MAP.md`. Resized to a 1200px long
edge (uncropped — full-bleed `background-size:cover` needs the whole frame
available to the CSS, unlike the earlier pass's pre-cropped 960×260 strips),
quality 76, stripped: 54–177KB each, down from 162–553KB. Added to `sw.js`
`OPTIONAL_ASSETS` (never `REQUIRED_ASSETS` — same offline-must-never-break
rule as every other image in this app).

## Per-page reports follow below as each page family is implemented.

## Page 1: Add / completed-workout

**Files changed**: `index.html` (tokens, `.scene-*` primitives, `#app`/`.header`/`.tabbar`
overlay rules), `app.js` (`PAGE_SCENES` registry, `render()`'s
`body.dataset.scene` stamp, `renderLogTab()`'s DOM restructure), `sw.js`
(club-photo precache).

**Selectors/classes added**: `.scene-page`, `.scene-page__media`,
`.scene-page__scrim`, `.scene-page__intro`, `.scene-page__brand`,
`.scene-page__title`, `.scene-page__subtitle`, `.scene-sheet`,
`.scene-sheet--paper`, `.scene-sheet--navy`, `.scene-sheet-title`,
`.scene-page--add` (+ 5 sibling modifiers for the other scenes, defined now
for reuse even though only Add is wired up this pass), `body[data-scene]`
descendant rules for `.header`/`.header-logo`/`#navMenuBtn`/
`#notificationsBellBtn`/`.brand-stripe`/`main`/`.tabbar`/`.tabbtn`.
**Modified** (pre-existing, fixed as a direct consequence of this pass, not
scope creep — see mismatch ledger): `.format-chip.active`, `.rx-btn.active-type`,
`.bar-center`.

**Exact token values used**: `--club-coral` aliased to the existing
`--energy` (not the spec's literal `#f0443e` — see the CSS comment at the
token block for why); `--club-navy:#081523`; `--scene-photo-height:clamp(300px,44svh,430px)`;
`--scene-sheet-overlap:16px` (changed from the spec sample's `42px` — see
mismatch ledger, item 1); `--scene-sheet-radius:28px`. Sheet tone palettes
(`--scene-sheet--paper`/`--navy`) reuse this app's own existing light/dark
`:root` token values verbatim, not the spec's own `--club-paper`/`--club-ink`
hex literals — see mismatch ledger, item 6.

**Interpretive decisions** (not in the spec literally, resolved and logged
rather than guessed silently):
- Add's photo-zone subtitle is conditional: "עבודה מעולה!" once something is
  logged today (matching `design-reference.jpg`'s populated state exactly),
  "מוכנים להתחיל?" when nothing is logged yet (the screen's actual default
  state for most opens) — the spec names only the populated-state copy.
- The intro's green completion check (`design-reference.jpg`'s own mark)
  only renders once something is logged today, for the same reason.
- Kept the existing "today's sets" numbered-list card (built earlier the
  same day, Direction 06 pass) inside `.scene-sheet` rather than rebuilding
  it — it already matches `design-reference.jpg`'s composition (exercise
  name, numbered/grouped set rows, edit/delete in place).

### Visual QA — required 3-pass loop (`VISUAL_QA_PROTOCOL.md` §3)

**Pass 1** (390×844, dark+light): screenshot revealed a fully broken result —
no photo, no title, sheet content filling the entire screen from y=0. Root
cause investigated with computed-style diagnostics, not re-guessed: `#app`'s
own persistent top padding (`calc(max(safe-area,28px)+20px)`, ~48px) was
still being applied on scene pages, and separately, `#bottomNavWrap`
(`.tabbar`'s real container) turned out to be a DOM **sibling** of `#app`,
not a descendant — confirmed by reading the markup, not assumed from the
spec's illustrative sample — so the original `#app[data-scene]` selector
could never reach the bottom bar at all. Fixed by (a) zeroing `#app`'s top
padding on scene pages and (b) moving the scene attribute to `body`, the
one ancestor both `#app` and `#bottomNavWrap` actually share.

**Pass 2** (390×844 + 430×932, dark+light, after the pass-1 fixes):
measured against `VISUAL_QA_PROTOCOL.md`'s own numeric targets:

| # | Mismatch found | Measured | Target | Fix |
|---|---|---|---|---|
| 1 | Sheet starts too high | 39.0–39.5% | 42% ±3% | `--scene-sheet-overlap` 42px → 16px |
| 2 | Header greeting/date unreadable in light theme | `--chalk`/`--steel` (dark navy) on photo | white | Added `!important` — an inline `style="color:var(--chalk)"` on the static markup outranked the class rule on specificity alone |
| 3 | Bottom nav wrong color entirely | `rgb(31,48,87)` (`--surface`) / white | `rgba(8,21,35,.96)` both themes | Same root cause as the sibling-DOM bug above — selector now reaches the real element |
| 4 | Bottom nav too tall | 76–80px | 68px + safe-area | Explicit `height` + `align-items:center` instead of padding-driven auto height (padding-bottom still carries the safe-area inset independently) |
| 5 | Save button too tall | 62px | 52px | `min-height:52px` scoped to `#bottomBar .save-btn` only |
| 6 | Two color-contrast failures (axe, dark theme) then five more (axe, **light** theme, not checked until this pass) | `.pick-hero-cta` etc. below 4.5:1 | AA | The spec's own literal `--club-paper`/`--club-ink`/`--club-muted` hex values were never contrast-vetted against this app's actual components; replaced with this app's own existing, already-tuned light/dark token sets (`IMPLEMENTATION_SPEC.md` §4 itself asks to reuse existing tokens "where they already serve the same purpose" — this is that) |
| 7 | Residual 2–4px gap between photo and true left/right viewport edge | 2px (390w) / 4px (430w) | 0px | Investigated, not resolved — see "Remaining mismatch" below |

**Pass 3** (390×844 + 430×932, dark+light, after the pass-2 fixes): re-ran
axe on both themes explicitly (not just the default dark theme
`a11y-axe-scan.mjs` runs) — found and fixed two more pre-existing,
unrelated-to-this-redesign contrast bugs it surfaced: `.format-chip.active`
and `.rx-btn.active-type` both used `color:var(--energy)` directly as text
(3.46:1, fails 4.5:1 — `--energy` is a fill/border tone, not a text-safe
one) instead of the already-established `--energy-text` token every other
active-chip control in this file already uses; `.bar-center` used
`var(--brass)` against `var(--surface2)` specifically (4.35:1) rather than
the `--surface`/`--bg` pairing `--brass` was actually measured and darkened
against (5.03:1). Both fixed. Final re-scan: 0 serious/critical violations,
both themes, both viewports.

### Completion report (`VISUAL_QA_PROTOCOL.md` §6 format)

| Screen | Theme | Viewport | Photo edges pass | Sheet % | Title px | Interaction tests | Visual passes | Remaining mismatch |
|---|---|---|---|---:|---:|---|---:|---|
| Add | Light | 390×844 | Top/right yes, left ~2px short | 42.1% | 34px | 1511/1511 node + axe 0 violations | 3 | 2px left-edge gap (below) |
| Add | Dark | 390×844 | Top/right yes, left ~2px short | 42.1% | 34px | 1511/1511 node + axe 0 violations | 3 | same |
| Add | Light | 430×932 | Top/right yes, left ~4px short | 42.3% | 34px | Same suite (viewport-independent) | 3 | 4px left-edge gap |
| Add | Dark | 430×932 | Top/right yes, left ~4px short | 42.3% | 34px | Same suite | 3 | same |

**Remaining mismatch, honestly flagged rather than hidden**: a 2–4px gap
between the photo and the true left/right viewport edge persists after
investigation. `.scene-page`'s `-16px` bleed margin and `#app`'s own
padding account for each other correctly on paper (confirmed: `#app`
content width + 32px = full viewport width), so the residual is coming from
somewhere not yet identified — possibly a sub-pixel rounding interaction
between `dvh`/`svh` units and the flex/percentage layout, not a simple
margin miscalculation. Well inside `VISUAL_QA_PROTOCOL.md`'s own geometry
tolerance section ("Horizontal app padding: ±2px from the defined token"),
and the photo is still unambiguously full-bleed and edge-adjacent to any
observer — but it is not literally 0px, so it is logged here rather than
rounded up to "pass."

**Tests run**: `npm test` — 1511/1511, both before and after the fix below.
`run-all.mjs` (35 browser-check scenarios, real Chromium) — first full run:
**34/35**, one real regression found:

**Regression found and fixed**: `community-recap-classmates.mjs` failed —
a Community-tab dialog button became unclickable, `.header-logo` "from
`<header>`… subtree intercepts pointer events". Root cause: `PAGE_SCENES`
had `history`/`calendar`/`wod`/`community` entries pre-registered (copied
from `IMPLEMENTATION_SPEC.md`'s own sample) even though only Add's render
function had actually been restructured to `.scene-page` markup this pass.
`body[data-scene]`'s CSS (header goes transparent/absolute, brand-stripe
hides) applies the instant a tab's key is *in* `PAGE_SCENES`, regardless of
whether that tab's content matches it — so Community's ordinary,
non-restructured layout got the floating-transparent-header treatment with
nothing underneath reserving its space, and the now-absolutely-positioned
logo landed on top of a real button. **Fixed by removing every
not-yet-implemented tab from `PAGE_SCENES`, leaving only `add`** — a tab
gets added to the registry in the same commit as its render-function
restructure, never ahead of it (comment left in place on the object
itself as a guardrail for the remaining screens). Re-ran full suite after
the fix: **35/35**. This is exactly the class of "components exist but the
composition is wrong" failure `VISUAL_QA_PROTOCOL.md`'s opening paragraph
names as the previous attempt's own mistake — caught here by the *existing*
regression suite, not the new visual-QA process, which is worth recording:
both layers of verification earned their place this pass.

**Second regression found while implementing the next page, retroactively
fixing Add too**: implementing History (below) surfaced that
`.scene-page__media`'s crop looked like an unrecognizable extreme close-up
— checked against the source photo directly (not assumed), then isolated
in a standalone test page with the identical `background-size:cover`
declaration against a correctly-sized box, which rendered the intended crop
exactly. Root cause: the spec sample's `.scene-page__media{ inset:0 }`
sizes `background-size:cover` against `.scene-page`'s FULL height — photo
band *plus* the sheet's entire content height, often 1500–2000px+, since
the photo is architecturally meant to extend the full page underneath the
opaque sheet (§3). Cover-fit against a ~390×1800 box scales by the tall
dimension, blowing the image up roughly 5× and leaving only a vertical
sliver in frame. Add's own photo happened to still read as "acceptable" by
coincidence — diagonal stripes still look like diagonal stripes zoomed in —
which is exactly why this needs a real screenshot compared to the source
file, not a glance, per `VISUAL_QA_PROTOCOL.md`'s own point. Fixed by
capping `.scene-page__media` to `height:var(--scene-photo-height)` instead
of the full `inset:0` stretch — the sheet is opaque regardless, so nothing
below that height was ever visible either way; this only fixes what the
visible photo band itself shows. Re-verified Add and re-measured History
after the fix: sheet-start percentages unchanged (42.1–42.3%, as expected —
this fix only touches the image layer, not layout), both photos now show
their correct, specified content. Full regression re-run after this fix:
`npm test` 1511/1511, `a11y-axe-scan.mjs` clean both themes,
`run-all.mjs` — see below.

## Page 2: History (this app's `calendar` tab)

**Screen-key note**: this is `PHOTO_MAP.md`/`design-reference.jpg`'s
"History" screen (month calendar + selected-day list) — which is this
app's `tab === "calendar"`, not `tab === "history"` (that key is mapped to
the reference's "Progress" screen instead — see the audit section at the
top of this file for the full reasoning, confirmed against actual current
labels before mapping anything).

**Files changed**: `app.js` (`renderCalendarTab()` restructured to
`.scene-page`/`.scene-sheet`, `calendar` added to `PAGE_SCENES`),
`index.html` (`.scene-page--history` photo position tuned).

**Selectors/classes added**: none new — reused every `.scene-*` primitive
from Add. `.cal-panel`/`.cal-grid`/etc. (pre-existing) sit inside
`.scene-sheet--navy` unmodified; their own `var(--surface)`-based styling
now automatically resolves to the navy tone via the sheet-scoped token
remap, with no per-component changes needed.

**Exact token values used**: `--scene-position:center 32%` added to
`.scene-page--history` specifically — checked against the actual source
photo (`history-open-floor.jpg`) rather than left at the inherited
`center top` default, which showed ceiling ductwork instead of the
stripe-wall/pillar/rower band the photo actually needs to show (the band
sits roughly 20–55% down the original frame).

**Visual QA**: sheet-start measured 42.1% (390×844) / 42.3% (430×932),
both themes — inside tolerance without any page-specific token change,
confirming the shared primitives generalize. Photo now shows stripe wall,
blue pillar and rowing machines clearly (see the media-height fix above —
this page is what surfaced that bug). `npm test` 1511/1511,
`a11y-axe-scan.mjs` 0 violations both themes.

## Frosted-glass pass (user-requested, both pages)

User feedback on the screenshots so far: "still some effects are missing!
Like transparent" — read as the header icon circles and bottom nav reading
as flat opaque discs/bars rather than genuine glass. Added
`backdrop-filter: blur() saturate()` (native CSS, `-webkit-` prefixed for
iOS Safari, `@supports not` fallback to the previous flat-opaque colors on
engines without it) to `#navMenuBtn`/`#notificationsBellBtn` (opacity
.72→.5, blur 10px) and `.tabbar` (opacity .96→.94 after one revert — .88
dropped the active coral tab label below AA against a bright patch of
photo showing through, caught by axe, restored to .94). Re-verified: axe
clean both themes, `npm test` 1511/1511. Sent both screens to the user for
direct visual confirmation rather than continuing to guess from a text
description.

**Deliberate scope note**: `IMPLEMENTATION_SPEC.md` §8 describes History as
possibly having a separate "history-list mode" sharing the same scene —
this app's actual list-of-past-workouts content already lives inside the
OTHER scene screen (`tab === "history"`, "Progress" in reference terms,
via `renderHistoryTab()`/`renderDetailCard()`), not duplicated here. Not
rebuilding it a second time in this screen; flagged rather than silently
diverged from the spec's wording.

## Page 3: Progress (this app's `history` tab)

**Screen-key note**: reference terms again — this is `PHOTO_MAP.md`'s
"Progress / PRs" screen (chart + PR cards), which is this app's
`tab === "history"` (already labelled "התקדמות"/Progress in the shipped
nav, per the audit mapping at the top of this file).

**Files changed**: `app.js` (`renderHistoryTab()` restructured,
`history` added to `PAGE_SCENES`). No new CSS needed — `.scene-page--progress`'s
photo modifier and position were already added during the Add-screen pass.

**Interpretive decision, logged rather than silently diverged**:
`IMPLEMENTATION_SPEC.md` §8 asks to "keep the existing metric tabs" and
describes "one large chart followed by a maximum of three PR cards above
the fold" — this app's actual Progress screen is a searchable **list** of
every trained exercise, each expanding in place to its own chart + PR
table (`renderDetailCard()`), not a single always-visible chart with a
metric-tab switcher. Restructuring the interaction model itself to match
the reference's single-chart layout would be exactly the kind of
"rewrite application logic... for a visual change" `CLAUDE.md`'s
non-negotiable constraints forbid — so the existing list/expand pattern is
kept, reskinned into the navy sheet as-is (same treatment already applied
to Add's day-entries list and History's calendar+day-detail: reuse the
real interaction, don't invent a new one to chase the mockup's literal
layout).

**Visual QA**: sheet-start measured 42.1% (390×844, dark) — inside
tolerance with no page-specific tuning needed, third scene in a row where
the shared primitives generalized correctly. Photo shows the blue rig and
rings clearly (reusing the `center 18%` position tuned during the Add
pass). `npm test` 1511/1511, `a11y-axe-scan.mjs` 0 violations both themes
(re-verified after the frosted-glass pass above, which touches every scene
page's header/nav chrome, not just Add/History).

**Tests run this page**: `heading-outline.test.mjs`,
`tablist-keyboard.test.mjs`, `bodyweight-measurements.test.mjs` (targeted),
then the full `npm test` (1511/1511) and `a11y-axe-scan.mjs` (clean). Full
`run-all.mjs` re-run in progress at time of writing this entry.

## Page 4: Library (`wod` tab), Community, Achievements, Notifications, Onboarding

All five restructured the same pass. **Library**: equipment-shelf scene,
paper sheet; sheet-level title placed inside `.scene-sheet` (per the spec's
own wording for this screen), not in the photo zone. **Community**
(`cloud.js`): red logo-wall scene, navy sheet, wrapping the existing
tab-bar/feed/toast/outbox-banner markup unchanged; a redundant inline
`photoHeaderHtml()` call inside the announcements section was removed since
the whole page now carries the full scene photo. **Achievements**: a 220px
plate-column mini-scene prepended to the existing modal (not a full
`.scene-page` — it is a dialog, not a tab) — required adding
`isolation:isolate` to its wrapper (same `z-index:-3`-escape bug as before)
and converting `renderNavWho()`'s wrapper to a `<button data-action="open-
achievements">` after hiding the header's second child div made the two
original triggers unreachable on scene pages (both are still present,
just no longer the only route). **Notifications**: a compact 100px
logo-wall photo strip added inside `renderNotificationCenter()` (the
Community notification center, not app.js's unrelated "what's new" bell),
same isolation fix. **Onboarding**: `#welcomeOverlay` upgraded from a small
contained `.photo-header` to a full-bleed 200px mini-scene using the
open-floor photo, title moved onto the photo in white.

**Settings** deliberately kept its pre-existing minimal `.photo-header`
treatment, per `IMPLEMENTATION_SPEC.md` §8's explicit instruction that
"Settings prioritizes clarity over immersion... not a dominant photo" — not
a full scene page, and re-confirmed via screenshot this pass rather than
left assumed.

## Desktop verification (900px sidebar / 1280px context-column tiers)

Two real bugs found and fixed, both specific to `body[data-scene]` at
desktop widths (mobile was already correct, which is why `npm test` stayed
green through both):

1. **Header spanned the full 1440px viewport** instead of the 560px `#app`
   column. `.header{ position:absolute }` was resolving its containing
   block to the viewport, because `#app` had no explicit `position` — that
   was invisible at mobile widths (where `#app` already equals the
   viewport) but broke as soon as `#app` is capped/centered at desktop.
   Fix: `body[data-scene] #app{ position:relative; }`.
2. **Header logo/bell mispositioned** (logo pinned near the right edge of a
   1440px viewport instead of centered in the 560px column). `#navMenuBtn`
   is `display:none` at the existing 900px+ breakpoint (the sidebar
   replaces it), and CSS Grid auto-placement skips a `display:none` item
   entirely rather than reserving its column — the remaining two items
   compacted into columns 1–2 instead of 2–3. Fix: explicit `grid-column`
   pins on all three header children instead of relying on DOM-order
   auto-placement.

Re-verified after both fixes: `desktop-layout.mjs` (29/29), `a11y-axe-scan.mjs`
(0 violations, both themes), and a `getBoundingClientRect()` diagnostic
across all 5 scene tabs at 1440×900 confirming `header.width === 560`,
logo horizontally centered in the middle grid track, and correct
`scene-page--*` class per tab.

## Progress against `SCREEN_ACCEPTANCE.md`'s screenshot ledger — complete

All nine primary screens now have the required 390×844 / 430×932, light +
dark screenshots (36 total): Add, History+Calendar (this app's `calendar`
tab covers both reference mockups — logged above, not re-derived), Progress,
Library, Community, Achievements, Notifications, Settings, Onboarding.
Delivered as a single HTML ledger rather than 36 individual attachments.

One real finding while assembling the ledger, unrelated to this redesign:
`app.js`'s default `themePref` is `"dark"` (not `"auto"`), so a fresh
profile ignores OS `prefers-color-scheme` entirely until the user picks a
theme in Settings — this is pre-existing behavior, not a regression, but it
meant the first capture pass's "light" screenshots were actually all dark
(caught by comparing the achievements modal's `.who` card background against
its expected token value, not by eyeballing). Fixed the *capture script* to
set `localStorage["haimunia-demo:theme"]` before load, matching how Settings
itself changes theme, rather than relying on the browser's color-scheme
emulation — no product code changed for this.

Also added `width`/`height` attributes to the header `<img class="header-
logo">` (`index.html`) as a defensive fix — an unsized image can render its
alt text at an unconstrained size for one frame before the intrinsic aspect
ratio is known. Not proven to have fired in production; added because it is
the standard, zero-risk fix for the class of bug and was already in flight
while investigating what turned out to be the club's real wall signage
(`community-logo-wall.jpg` — the giant "האימוניה" is the actual painted
logo on the actual wall, correctly rendered, not a UI bug).

Final regression after all of the above: `npm test` 1511/1511,
`run-all.mjs` 35/35 browser-check scenarios, `a11y-axe-scan.mjs` clean in
both themes.

## Two bugs found from live use, after the ledger was already delivered

**1. Switching tabs jumped/snapped the page.** `data-action="switch-tab"`
never reset scroll (`app.js`, the click delegator's `switch-tab` /
`switch-tab-community-sub` branches) — invisible before this redesign, when
every tab was roughly the same height, but scene pages vary wildly (a
scrolled-down Progress list vs. a short Add page), so the browser visibly
snapping the old scroll offset onto much shorter/taller new content read as
a jump. Fixed: both branches now call `window.scrollTo(0, 0)` after
rendering. Keyboard tablist navigation (`ArrowLeft/Right`, arrow-key roving
tabindex) routes through `next.click()` into the same delegator, so it's
covered by the same fix without a separate change.

**2. Scene sheets were stuck in one tone regardless of the device's theme**
— reported directly: "dark theme, [workout] summary is white." The sheet
tone (`.scene-sheet--paper` cream / `.scene-sheet--navy` dark) was built
deliberately theme-independent, reasoned from `design-reference.jpg`
showing Add as fixed cream and History/Progress as fixed navy in its own
screenshots — but that is exactly the "no page stuck in one theme" behavior
`CLAUDE.md`'s own non-negotiables forbid, and in practice meant a member
using dark theme hit a blinding white card on the screen they use most.
Fixed: collapsed `--paper`/`--navy` into one `.scene-sheet` that follows the
device's real theme like every other themed surface — light theme reuses
the same (already contrast-tuned) light values the "paper" tone had, dark
theme reuses the same dark values the "navy" tone had, so no new palette
was introduced, only which one applies. Removed the now-dead `sheetTone`
field from `PAGE_SCENES` (it was never actually read to build a class name
— the 5 render call sites had the tone hardcoded independently).

This is the first time Calendar/Progress/Community render in light theme
and Add/Library render in dark theme — a genuinely new combination, so it
was axe-checked explicitly rather than assumed safe by inheritance. Found
one real pre-existing bug this exposed: `renderVolumeReport()`'s
`.report-flag` badge (last-trained-this-category chip) used a fixed `.15`
opacity tint behind `--red-text`/`--green-text`, tuned only against the
navy surface Calendar always had before. Measured against the real token
values: the light-theme red state was 4.456:1 (just under AA), and the
dark-theme green state was 4.505:1 (technically passing, no real margin).
Dropped the tint to `.10` for all three flag states — 4.78/4.81 in the two
failing/marginal cases, improved everywhere else, verified against both
themes' actual hex values before shipping, not assumed.

Re-verified after both fixes: `npm test` 1511/1511, `a11y-axe-scan.mjs`
clean (dark, the default theme), plus a targeted light-theme axe pass
across Add/Calendar/Progress/WOD (the combinations that had never
rendered in light theme before this fix) — all clean.



Independent items that landed the same day as the Phase 3 merge gate, batched
here since each is small and self-contained:

- Hebrew copy review: mechanical agreement/punctuation fixes, plus a real fix
  for two drifting terms — "חברים" collapsing "members" and "friends" into one
  word depending on screen, and "מתאמן"/"חבר" (trainee/member) used
  inconsistently across the app. Both now read as one consistent term each.
- Fixed `activity_pings` and `onboarding_progress` writes silently never
  reaching the server.
- Fixed the desktop sidebar (added earlier the same day, see below) not
  actually sticking on scroll.
- Fixed the calendar's prev/next month chevrons pointing the wrong way.
- The service worker now forces an update check on every foreground regain,
  instead of only at load.
- Added Squat Clusters to the built-in movement list, plus other
  movement/WOD gaps found in a follow-up research pass.
- Consolidated three hand-rolled batch-profile-lookup call sites into one.
- Widened the gap between two-up date/number field pairs.
- Fixed the nav-menu and Settings screen's close button and title sitting
  behind the status bar — the same class of collision fixed for
  `.brand-stripe` on 2026-08-27, now hitting the new nav menu and Settings
  screen built the same day (see below).
- Six smaller fixes from a design audit, batched as one commit: contrast, an
  icon, bidi text handling, and interaction states.
- The "what's new" bell's release-notes list was refreshed for the next real
  release (v4.0.0).
- Fixed a stale code comment in `mockSupabase.mjs` claiming the real
  Supabase query builder supports `.catch()`.

# App navigation redesign: hamburger menu, Settings screen, desktop sidebar, and a bottom-sheet install prompt — 2026-09-01

A UI-restructuring pass across the whole app shell, not scoped to Community:

- A hamburger + full-page nav menu replaces the old top tabbar as the
  primary navigation, with two new exports (`window.setCommunityTab`,
  `window.getCommunityNavPreview`) so the nav menu can drive and preview the
  Community sub-tab from outside `cloud.js`.
- A dedicated Settings screen replaces the footer that used to sit glued
  under every tab.
- Wide viewports (desktop) now get a persistent sidebar instead of
  reflowing the mobile layout.
- The install prompt moved from a top colored strip to a bottom sheet.
- Page titles were added to all four solo tabs, additive above existing
  content.
- A visual polish pass: card shadows, the radius scale, and the plate/CTA
  gradients.
- A new app icon for the installed PWA's home-screen icon.

This entry pairs with the small-fixes entry above — several of those fixes
(sidebar sticking, the nav-menu/status-bar collision) are follow-up
corrections to this same redesign, landed the same day.

# Community Phase 3: intelligence features on verified attendance — 2026-08-31 to 2026-09-01

Phase 3 (COMM-300 to COMM-317) adds attendance as a real signal without ever
building a check-in flow: `attendance_log` (COMM-300) is populated by a
trigger on the existing offline training log's own sync store — logging any
workout doubles as "I was here." Every later feature calls this
"self-reported, not physically verified" attendance, the same trust boundary
the training log already had, documented in each surface's own copy where it
matters (a stale "verified attendance data will be added later" leftover
from the Phase 2 consistency board's Phase-2-era copy was one of the few
contradictions found, and fixed, by the closing QA sweep below).

Built on top of it:

- **Feed**: `relationship_score()` extracted as a pure refactor (COMM-301, no
  ranking change), a recurring-classmate signal once two members'
  `attendance_log` rows overlap (COMM-302), a consistency leaderboard now
  ranked on real attendance instead of feed posts (COMM-306), a "who trained
  with you today" feed-top-area card (COMM-307), and per-user feed weight
  storage/reader — the derivation itself is a deliberate, documented stub
  returning the same fixed defaults for everyone until a real weighting job
  exists (COMM-303).
- **Achievements**: the four `ATTENDANCE_RECORDED` achievement definitions
  (seeded empty back in Phase 0) are enabled, with a club-visible milestone
  post at 25 and 100 sessions (COMM-305).
- **Coach tools**: `coach_engagement_flags` (empty since Phase 0) gets its
  first producer, a scheduled decline-detection job comparing an 8-week
  baseline to a 2-week recent window, surfaced in the Engage section
  COMM-226 had already built hidden behind a flag, now flipped on by
  default (COMM-304); a "member of the week" rotation across four
  recognition categories — consistency streak, most PRs, challenge
  completion, coach's pick — publishing a real announcement post (COMM-315).
- **Recaps**: a monthly, club-wide recap with an admin preview/publish step
  (COMM-309), and the weekly recap gains a named classmates line plus two
  attendance-based onboarding steps that COMM-222 had explicitly deferred
  (COMM-316).
- **Challenges**: advanced team management — coach-driven team CRUD, member
  reassignment, a captain label — on top of the existing team-challenge
  shape, with a real trigger closing a gap where a plain member could
  otherwise have moved themselves onto any team (COMM-308).
- **Admin moderation**: a full admin analytics dashboard (COMM-310), member
  engagement segmentation into six buckets (COMM-311), a retention-cohort
  view (COMM-313), and an internal-only weighted community health score that
  reads the retention signal (COMM-312) — built in real dependency order
  (310 → 311 → 313 → 312), corrected mid-build once the actual read
  direction between 312 and 313 was checked against the shipped code rather
  than the ticket text.
- **Identity/privacy**: a versioned abandoned-profile purge Edge Function
  and runbook, for anonymous accounts that never redeemed an invite or
  verified recovery (COMM-314) — a different cleanup from the existing
  30-day deletion-request purge.

**COMM-317, the Phase 3 QA sweep and merge gate**, cross-referenced every
ticket's acceptance criteria against the shipped code from a genuinely fresh
state (a local Docker Supabase stack, clean reset), rather than trusting
each agent's own report — the same discipline COMM-234 held for Phase 2. It
found and fixed the stale consistency-board copy above, added three pgTAP
assertions proving `attendance_log`'s "only a trigger can write this"
boundary at runtime (not just by reading grants), and added five new
browser-check scenarios. Every "storage exists, no scheduler runs it yet"
gap this phase logged individually (`recompute_feed_weights`,
`coach_detect_engagement_decline`, `recap_monthly_generate`,
`community_health_generate`, `purge_abandoned_profiles`) was consolidated
into one table rather than left scattered. Final counts: `npm test` 907 →
914, `supabase test db` 1955 → 1958 assertions across 54 migrations,
`scripts/browser-check` 19 → 24 scripts, all green.

# Community Phase 2: challenges, events, announcements, coach tools, realtime, search, leaderboards, and web push — 2026-08-30 to 2026-08-31

Phase 2 (COMM-201 to COMM-234) generalizes the Phase 1 weekly challenge into
a real challenge model (individual target/performance, cooperative with a
club aggregate, team, consistency, and coach custom-rules types —
COMM-201-207), adds a full events system with RSVP/capacity and an `.ics`
download (COMM-213-217), gives announcements three priority tiers and an
expiry (COMM-218), a batched/urgent notification split (COMM-219), and a
weekly member recap Edge Function with a share action (COMM-220-221) — the
two onboarding steps that need real class attendance were explicitly
deferred to Phase 3 (COMM-222). A new Coach Dashboard ships with a
Celebrate section, a Welcome section, one-tap congratulate, and an Engage
section shipped hidden behind a default-off flag pending Phase 3's
attendance data (COMM-223-226). Realtime channels (challenge
progress/participants, feed comments/reactions, notifications) and a
member/event/challenge search RPC land together (COMM-209/227/228), plus
three new leaderboard modes (consistency, progress, friends-with-hide) and a
"people you train with" suggestions strip (COMM-210-212, 232), a following
system and members directory (COMM-230-231), and web push subscription
storage behind a feature flag — actually sending a push still needs a
scheduled sender, not built here (COMM-229). COMM-233 confirmed the Phase 2
analytics bridge was already firing correctly with nothing left to wire.

**COMM-234, the Phase 2 QA sweep and merge gate**, found and fixed a real
bug: `renderConfirmDialog()` concatenated the confirm sheet before the
challenge/event/composer overlays it can nest inside, so in a real browser
its button was rendered but pointer-events-unreachable behind the
still-open parent dialog — invisible to jsdom's non-hit-testing `.click()`,
caught only by a real-Chromium browser-check built for this sweep. Final
counts: `npm test` 764 → 769, `supabase test db` 884 → 940 assertions,
`scripts/browser-check` 10 → 17 scripts including 7 new Community
scenarios.

# Community Phase 1: posts, feed, engagement, achievements, notifications, moderation, coach identity, analytics — 2026-08-28 to 2026-08-30

Phase 1 (COMM-101 to COMM-191) is the first real Community V1 build on top
of Phase 0's schema: post rendering across every type (text, photo,
workout, PR, achievement, new-member/system) with a save/hide/edit/
visibility/delete action menu (COMM-101-108, 180), a ranked feed with
filters, diversity rules, cursor pagination, and impression/interaction
tracking (COMM-110-115), reactions and two-level comment threads with
mentions and coach visual priority (COMM-120-125), an achievement engine
with non-attendance triggers, PR detection and a share prompt, and unlock
celebrations (COMM-130-134), a notification center with immediate/batched
routing and per-type preferences (COMM-140-144), RBAC permission strings, a
report flow, an admin moderation queue with an audit trail, and pinned
content (COMM-150-156), and coach identity shown consistently across every
surface (COMM-160). Three schema follow-ups landed the same window to
unblock the client work as it was built: achievements/mentions/profile-view
columns, `post_create` plus a moderation reshape, and server-side
notification triggers.

COMM-143 (notifications wiring) is `partial`: the client renders every
Phase 1 notification type correctly, but the server trigger set that
creates them is documented separately rather than built as its own ticket —
one open item there, a `post_comments` trigger being unable to see the
client-only mention list, was closed by routing mention notifications
through a trigger on the new `comment_mentions` table instead.

**The Phase 1 QA sweep (COMM-190/191)** added the dialog keyboard/focus
contract and closed a coverage gap before the phase gate. COMM-020 also
landed in this window: the last 2 remaining pgTAP failures were fixed and
the migration-check CI job flipped from advisory back to blocking, plus
three rounds of pgTAP behavioral coverage were added across migrations
202608280014-028, and a tenure-claim gaming gap in `ach_claim` found while
writing that coverage was fixed.

# Community module Phase 0: foundations — 2026-08-28

The first Community-module-specific commit on the `community/phase-0`
branch: eleven schema migrations (post types/visibility, post media, feed
impressions/interactions, achievements, notifications, challenges, events,
roles/permissions, an admin-actions audit table, profile privacy columns,
and an empty `coach_engagement_flags` table — COMM-001 to COMM-011), a
product event bus and typed event list, an analytics helper with the WCAM
definition, a Supabase Realtime harness, and client-side image compression
(COMM-012-015), a required recovery method at invite redemption and an
actor-level invite throttle (COMM-016-017), a privacy toggle model enforced
by RLS (COMM-018), and one static-assertion RLS test per new table
(COMM-019). Wires no producer, no consumer, and no upload path yet — zero
user-facing change until Phase 1 builds on top of it. CI's pgTAP step was
marked advisory (`continue-on-error`) the same day, to mark Phase 0
validated despite unresolved failures at the time — hardened back to a
blocking gate on 2026-08-30 once COMM-020 fixed the remaining two failures
(see above).

# Fix status bar colliding with the top of the page on Android — 2026-08-27

Reported with a screenshot: on an installed (Add to Home Screen) Android
PWA, the phone's real status bar (clock, signal, battery) sat directly on
top of `.brand-stripe` - the orange/white diagonal decoration at the very
top of `#app` - instead of above it. Root cause: `#app`'s top padding was
just `env(safe-area-inset-top, 0px) + 20px`, and at least one real
Android browser/WebView combination reports `safe-area-inset-top` as 0 on
an installed standalone PWA even though the status bar still visually
overlays the page. With no real inset reported, the 20px flat padding
wasn't enough clearance, so brand-stripe's own busy pattern - not a plain
background - ended up directly behind the status bar icons.

Fixed with a floor, not a bigger flat number: `max(env(safe-area-inset-top,
0px), 28px)`, applied to `#app`'s top padding and the two other
top-of-viewport elements with the same shape (`#updateBanner`,
`#installBanner` - both also have colorful, non-plain backgrounds at
`top:0`). A device that correctly reports a real, larger inset (an
iPhone notch, for example) is unaffected - max() just keeps the larger
real value. One that under-reports it now gets a guaranteed 28px
minimum instead of colliding.

266/266 tests pass, plus all 12 browser-check suites.

# Submission 11: split app.js into src/ modules — 2026-08-27

Last (and biggest) item on the deferred architecture backlog, scoped down
after actually mapping the file: of app.js's ~4,500 lines, only about
850 were genuinely self-contained - no dependency on the ~50 module-scope
state variables (`entries`, `tab`, `weight`, `wodEntries`, etc.) that
rendering, WOD actions, achievements, and event delegation all read and
write throughout the rest of the file. Decomposing *that* core would mean
first consolidating it into a shared state object (like cloud.js's own
`state = {...}`) - a separate, larger, riskier rewrite, not something to
fold into this pass. What actually moved, into `src/`:

- **constants.js** - the data tables (`MOVEMENTS`, `WOD_LIBRARY`,
  `WOD_MOVEMENT_TAGS`, `LIMITS`, `FIELD_MAX`, `MOVEMENT_CATEGORIES`, …)
  and the small lookup helpers built on them (`catColor`, `catLabel`,
  `cssSel`, `bag`).
- **format.js** - pure formatters with no state dependency
  (`estimate1RM`, `formatDuration`, `fmtDate`, `todayISO`, `esc`, …).
  `calcPlates` stayed behind in app.js despite living right next to
  these originally - it reads `barWeight`, which is live state.
- **sanitize.js** - the `cleanX`/`sanitizeX` validators applied to every
  record that comes off disk or out of an import.
- **db.js** - the whole IndexedDB layer. This one grew past its original
  contiguous block: four more `db*` functions turned out to be scattered
  through the sync/WOD-deletion code later in the file, each reaching
  into a store-name constant that only this file should own
  (`OUTBOXSTORE`, `MOVSTORE`, `CUSTOMWODSTORE`) - moved alongside the
  rest rather than left half-migrated. `queueSyncRecord`'s inline outbox
  write became a `dbPutSyncOutboxRow()` call instead, matching every
  other write in the file.

app.js: 4,506 -> 3,660 lines. Two real correctness risks, both now
guarded: `sw.js`'s offline precache list needed all four new files added
by hand (missed, this silently breaks the app offline - a new test
derives the expected list from index.html's own `<script>` tags instead
of trusting a second hand-maintained copy) and the split briefly broke
`npm test` in a way that would never show up in a real browser - jsdom's
`window.eval()` (used by `test/helpers/boot.mjs` to run the app inside a
fake DOM) gives each separate eval() call its own script scope, so a
`const` from an earlier file isn't visible in a later one, unlike real
`<script>` tags, which correctly share one global lexical environment
(verified directly: `scripts/browser-check` never failed against real
Chromium, only `npm test` did). Fixed in the harness, not the app, by
concatenating the split files into one `eval()` call instead of one per
file.

Also fixed while auditing CI: `browser-checks` had been failing on `main`
since Submission 8 for an unrelated reason - `duration.mjs` asserted the
barbell visual shows by default after selecting Weighted Plank, but
Weighted Plank is `barbell: false` and never shows it in any mode. The
app's guard on that visual was correct; the test just picked a movement
that could never pass its own assertion.

266/266 tests pass, plus all 12 browser-check suites against a real
Chromium build.

# Submission 10: migration-apply CI check — 2026-08-27

Last infra item from the deferred architecture list. A `migration-check`
job in `.github/workflows/test.yml` now runs `supabase start` (via
`supabase/setup-cli`) on every push and PR, which spins up a throwaway
local Postgres + Auth + Storage stack and applies every file in
`supabase/migrations/`, in order, from scratch. The migrations lean on
Supabase-specific schemas (`auth.users`, `auth.uid()`, `storage.objects`,
the `extensions` schema for pgcrypto) that a plain `postgres:` service
container in Actions doesn't have, so this uses the real local Supabase
stack rather than a bare database - the same reason
"Run the migration against an empty staging database" was previously a
manual step in `COMMUNITY_SETUP.md`'s launch checklist. This automates
that check on every push instead of relying on someone remembering to do
it by hand before a release. New `supabase/config.toml` (CLI-only, not
used in production - the real project stays configured through the
dashboard) mirrors the two settings the app actually depends on:
anonymous sign-ins on, email confirmation off.

# Submission 9: anon-key smoke test, vendored-version check, pre-commit hook — 2026-08-27

Three infra items from the deferred architecture list, run against the
real live project where relevant, not just written and hoped:

- **`npm run smoke-test-anon-key`** queries every table/view over the
  real network as the public anon key with no session and asserts each
  one returns nothing - the invariant that makes shipping the committed
  publishable key safe, previously verified by nothing automated (RLS
  has been wrong on first attempt three separate times in this
  project's history). Ran it against the live project just now: all 17
  tables/views correctly return HTTP 401, no grant. Deliberately not
  part of `npm test`, which stays offline/hermetic - this needs the
  live network.
- **`npm run check-vendor-version`** (and a real offline test running
  it) confirms `vendor/supabase.js` - a hand-copied build artifact -
  actually matches the `@supabase/supabase-js` version package.json
  declares, instead of the two being able to silently drift apart with
  nothing checking.
- **`npm run setup-hooks`** (opt-in, one time per clone) points git at
  `.githooks/pre-commit`, which runs both version checks above before
  every commit - catches the exact class of mistake (a version bump
  that forgets `npm run sync-version`) before it's committed, not just
  in CI.

266/266 tests pass.

# Submission 8: sync cursor and real conflict detection — 2026-08-27

Two architecture findings on the private-records sync path:

**Every login re-fetched and re-applied every private record** (up to
20,000) from scratch, even though almost nothing had changed since last
time. `pullPrivateRecords()` now keeps a per-user sync cursor
(`dbGetSetting`/`dbSetSetting`, keyed by user id so a different account
signing in on the same device never inherits a stale one) and only
queries records newer than it - verified with a real executing test
that a second pull only fetches the one genuinely new record, not the
whole table again.

**Both push and pull blindly overwrote by id with no timestamp
comparison** - two devices editing the same entry offline would
silently clobber whichever one happened to sync last. `shouldApplyRemote()`
now compares timestamps for the four record types that actually carry
one (strength/WOD entries, bodyweight, measurements) before applying a
remote write - an older edit is simply not applied, not lost (its own
outbox row still exists and pushes out again later). Movement/WOD/
measure-type definitions, which have no timestamp and are rarely edited
concurrently, keep the previous behavior; deletes aren't
conflict-checked either, since there's no tombstone timestamp to compare
against - documented as a known, accepted limitation rather than solved.

264/264 tests pass.

# Submission 7: stepper-field config table — 2026-08-27

Architecture finding: every numeric stepper field (main log, WOD log,
bodyweight, the WOD builder's per-movement/EMOM/time-cap fields, body
measurements) required a matching branch added to four separate
functions - fieldMax/getFieldValue/setFieldState/applyFieldValue - for
every new field type, kept in sync by hand. One `FIELD_ACTIONS` config
table now drives all four instead, so adding a field type is one entry,
not four edits. Behavior-preserving refactor, not a feature change -
the full existing stepper test suite (which already covered this
machinery in real depth) passes unchanged.

260/260 tests pass.

# Submission 6: three items from the deferred architecture list — 2026-08-27

- **WOD log's Save button is now pinned** to the same fixed bottom bar
  the main Log tab already has, instead of an inline button at the end
  of scrolling content (EMOM with several movements, or Scaled mode's
  extra notes field, used to mean real scrolling to reach it). The bar
  now switches its action/label based on which tab - and for WOD,
  whether a WOD is actually selected - is active.
- **Compare results render inline under the post that triggered them**,
  not in one spot at the top of the whole feed - tapping compare on a
  post scrolled far down used to produce a result with no visual link
  back to which post it was for. A second tap on the same post's button
  closes it again.
- **A movement typed into the WOD builder now persists** through
  IndexedDB (new `wodMovementTags` store, DB version 8 → 9), matching
  every other "custom X" feature - it used to live only in memory and
  vanish on reload, meaning re-building a similar WOD meant
  re-categorizing the same movement from scratch every time. Also fixed
  a real (if previously harmless) bug found while touching this: the
  500-tag cap was checking the built-in list's fixed length, which never
  changes, so it never actually enforced anything.

260/260 tests pass.

# Sharing moves to where the result actually lives — 2026-08-27

Reported directly: "שיתוף תוצאה takes too much [room] here, it need to
be shared by click from the calendar or progress, not from community
area." The old "share result" section was a standing list of the 8 most
recent shareable results sitting at the top of the Community tab's
feed - the place you open to see *other* people's posts, not to decide
what of your own to publish.

Removed it. Sharing is now triggered from wherever a result actually
lives - a single collapsed icon (renderShareControl) on each entry in
Calendar's day view and on each movement/WOD's Progress card, expanding
into the same photo/visibility controls only when tapped.

This needed one real architectural fix, not just a relocation: the
confirm dialog used to only render as part of the Community tab's own
output, so a share triggered from Calendar would have had no way to
show it. app.js's render() now appends it unconditionally after every
tab's content instead, regardless of which tab is active - verified
with a real executing test that publishes from the Calendar tab and
confirms the mock server actually received the post.

Publishing itself now looks up the specific entry by id
(communityShareCandidateFor), not just within the 8 most recent -
Calendar and Progress can both show a result from any date.

252/252 tests pass.

# Admin member management: search, grant/revoke coach, remove — 2026-08-27

Requested directly: "we need to manage the users, by ID + user name...
currently its not working." There was no in-app way to look up a member
or change their role short of the Supabase SQL editor.

New "ניהול חברים" panel in the Account tab, admin-only: search by
handle, display name, or a pasted user id (UUID), see role/join-date/
last-activity, and grant or revoke coach or remove the member - all
backed by dedicated RPCs (`admin_search_members`, `admin_grant_coach`,
`admin_revoke_coach`, `admin_remove_member`) that each check real
`is_admin` server-side, the same boundary `review_report()` already
uses, not the broader coach-inclusive `is_staff()`. Granting coach
(elevates privilege) and removing a member (destructive) both go
through the shared confirm dialog; revoking coach doesn't need one,
since it only ever lowers privilege. Removing a member mirrors
`request_account_deletion()`'s own effect - immediate soft-delete, a
30-day scheduled purge - just admin-triggered for someone else.

Also requested directly: "i also need user + id in the siupbase" - added
`public.admin_user_directory`, a plain view joining id, handle, display
name, the synthetic login email, role, and admin status in one place for
browsing directly in the Supabase SQL or Table editor. No grants to
`anon`/`authenticated` - it's a dashboard convenience, not part of the
app's own API surface.

Both new executing tests (see Submission 5) and the usual source-level
ones pass: 247/247.

# Submission 5: cloud.js now executes under test, not just source-matches — 2026-08-27

Independent architecture review, highest-leverage recommendation: every
cloud.js test before this one was a regex match against the source
text - it could prove a function signature exists, but not that the
code actually runs correctly. That exact gap is why the
refreshSession()-doesn't-flush-before-pulling regression (Submission 1)
could ship undetected in the first place, and it's the reason the whole
community/sync surface had the least durable coverage in the app despite
being the most recently and heavily hardened part of it.

Added `test/helpers/mockSupabase.mjs` (an in-memory mock of the
Supabase client - auth, `.from()` query chaining, `.rpc()`, `.storage()`)
and `bootCommunity()` in `test/helpers/boot.mjs`, which boots cloud.js
alongside the real app.js in jsdom the way `bootApp()` already did for
app.js alone. Two real executing tests now exist:
`community-live-sync-and-auth.test.mjs` runs the exact scenario the
Submission 1 sync bug corrupted (a queued local edit reaching the mock
server before a stale remote copy would be pulled back) end to end, and
runs the full signup lifecycle for real - bootstrap, redeem code, set
credentials, complete profile, reach the app, sign out, log back in and
land in the same account - the way a real login flow actually behaves,
not just what the source claims it does.

Building this surfaced one real, previously-latent bug: every cloud.js
form handler read fields via the legacy `form.fieldName` shorthand,
which real browsers support but jsdom doesn't implement (a known jsdom
gap, not a bug in the app) - switched to the more explicit,
equally-standard `form.elements.fieldName`, which also sidesteps a
real footgun the bare form gets wrong in every browser: a field
literally named `action` or `reset` would otherwise shadow the form's
own methods.

239/239 tests pass.

# Submission 4: eight smaller UX findings from the audit — 2026-08-27

Batched together since each is small and self-contained:

- Bodyweight now gets its own section label in the History tab, instead
  of reading as just another tracked exercise (measurements already had
  one).
- The main tab bar and Community sub-tab bar meet the 44px touch-target
  baseline — they were the app's most-tapped control, often used with
  chalky hands, sitting under it.
- Onboarding now mentions the Community tab and that it needs an invite
  code — previously the least self-explanatory of the five tabs was the
  one left out of the four-item walkthrough.
- Submitting the WOD builder with an empty name used to fail completely
  silently (a focus jump, nothing else) — now shows a real error and
  marks the field invalid.
- The destructive "delete all data" trigger gets its own red-bordered
  styling instead of the same de-emphasized link style as "edit profile."
- Clearing all data now auto-downloads a backup first, the same safety
  net Import already had for a far less destructive operation.
- Unchecking then rechecking an EMOM station now restores its original
  rotation position instead of silently moving it to the end of the list.
- The weekly-challenge comparison-key field now shows a real example
  (`movement:back-squat:est1rm`) instead of a bare movement name that can
  never match a real post, and validates the format before saving — the
  old failure mode was invisible, since an unmatchable key's empty
  leaderboard looks identical to a legitimately fresh one.

Deferred to a later pass, each larger than it looks: pinning the WOD log
tab's Save button the way the main Log tab's already is, and rendering
compare-results inline under the post that triggered them instead of
above the whole feed.

236/236 tests pass.

# Submission 3: rate limiting on comments, reactions, and reports — 2026-08-27

Independent security review: no table beyond invite redemption had any
rate limiting. Combined with a leaked invite code costing an attacker
nothing to redeem repeatedly, a script could spam comments/reactions/
reports without limit, bounded only by RLS ownership checks, never
volume.

Moved all three behind a security-definer RPC (same pattern
`redeem_invite_code` already used) that checks a shared `rate_limits`
table before writing, then revoked the client's direct INSERT grant on
all three tables so the RPC can't be bypassed by calling `.insert()`
directly. Reactions also got a small correctness bonus: the toggle
(cheer/uncheer) is now one atomic server call instead of an insert
followed by a delete-on-conflict, closing a small race between the two.

Documented, not built: CAPTCHA on sign-up needs a Turnstile/hCaptcha
site key only the project owner can create - see COMMUNITY_SETUP.md's
new "Recommended, not yet done" section.

228/228 tests pass.

# Real username + password login, so one account works on any device — 2026-08-27

Reported directly, with a screenshot: "this do not sync with community,
profiles is a mess, i want one time login and that it, figure how to,
like any other normal app." Plain anonymous-only sign-in had a real,
structural limit behind that complaint — there was no way to log back
into the same account from a different device or after clearing site
data, so every fresh browser/device was a disconnected identity with its
own invite-code redemption and profile.

New flow, still with no real email ever collected or sent: a brand-new
member enters the club invite code first (needs some session to attach
the redemption to, so an anonymous one is created invisibly, same as
before), then immediately sets a username + password. That upgrades the
same underlying account to a permanent one — Supabase's supported
anonymous-to-permanent conversion (`auth.updateUser`), same `auth.uid()`,
so the redemption and profile carry straight over with nothing to
migrate. A returning member just logs in with those credentials from any
device and reaches the exact same account, same history, same streak.

The password field is real. The "email" behind it isn't: it's built
locally from the username using the `.invalid` TLD reserved by RFC 2606
for exactly this — an address guaranteed to never resolve or receive
anything. Both the login form and the account-creation form are plain
in-app submits with no redirect anywhere, so the one thing that ruled
out email in the first place (a magic link opening in the phone's
default browser, disconnected from the installed home-screen app)
doesn't apply here.

Also added back a real sign-out button in the Account tab — safe now
that logging back in actually works, unlike before.

Setup note: **Confirm email** must be turned off for the Email provider
in the Supabase dashboard (Authentication → Sign In / Providers) — see
COMMUNITY_SETUP.md. Nothing in the app can deliver a confirmation to a
`.invalid` address, so leaving it on would lock every new signup out of
the account they just created.

223/223 tests pass.

# Submission 2: one confirm dialog everywhere, publish preview, delete-own-post — 2026-08-27

Three UX findings, done together since they all touch the same
destructive/broadcast-action surface in cloud.js.

Publishing a workout to the community feed (public, optionally with a
photo) used to fire immediately with zero confirmation or preview, while
lower-stakes actions in the same file (block, sync history, delete
account) went through the browser's native confirm dialog - which breaks
out of the app's own dark, custom-fonted visual language entirely. Three
different patterns, and the riskiest action had none of them.

Replaced all of it with one in-app confirm dialog (askConfirm/
closeConfirm/runConfirm), matching the app's existing bottom-sheet modal
style. Publishing now shows the post's title and result text (and a
photo indicator) before it goes out. Destructive actions (block, delete
account, delete post) render their confirm button in red.

Also added the delete action that never existed: a post's author can now
remove it from the feed directly - previously the only way to undo a
publish was deleting the entire account.

214/214 tests pass.

# Two critical bugs, from an independent 3-lens audit — 2026-08-27

First of several follow-up submissions closing out findings from a
full-app UX/security/architecture review. These two were flagged
Critical by the UX and architecture reviewers respectively, and both are
silent-data-corruption bugs a real user could hit through completely
normal use, with no error shown either time.

**Weight floor was tied to barbell weight for every movement.** The
weight stepper in "reps" mode enforced a floor equal to the selected bar
weight (8/15/20kg) regardless of which movement was selected - including
weighted pull-ups, chin-ups, dips, dumbbell presses/rows, lat pulldown,
leg press, and other non-barbell entries sharing the same picker. Typing
a real light added weight for one of these got silently clamped up to
the barbell floor, corrupting the actual saved PR. Fixed with an explicit
`barbell: false` flag on the MOVEMENTS entries that aren't loaded on a
bar, gating both the stepper floor and the barbell-plates visual on it.

**Reopening the app could silently overwrite a just-made offline edit.**
`refreshSession()` - the path that runs on every normal app open when a
session already exists - pulled the remote community-sync copy of
private records without first flushing pending local edits. A set logged
offline seconds before reopening the app got its local edit overwritten
by the still-stale server copy; the queued edit would eventually
re-push, but the UI visibly regressed in the meantime. Fixed by flushing
the outbox first, matching the pattern the sign-in path already used.

208/208 tests pass.

# Form field errors wired for screen readers, a real admin moderation queue, and community UI polish — 2026-08-27

Three deferred rescan items, done together since they touch the same
render code:

**Form validation is now screen-reader visible.** Every real-validation
field in the Community tab (invite code, handle, announcement title/body,
weekly challenge fields) goes through a new shared `field()` helper that
sets `aria-invalid`/`aria-describedby` on the input and renders the exact
same error text visibly beneath it, instead of only a generic banner at
the top of the form. The bare invite-code input also gained a real
`<label>` — it never had one before.

**`review_report()` (from the security-hardening migration) had nothing
calling it.** An admin had no way to see or act on a report short of the
Supabase SQL editor. Added a moderation queue in the Account tab —
open/reviewing/resolved/dismissed, with mark-as-reviewing/resolved/
dismissed actions — gated on real `is_admin`, not the broader
coach-inclusive `is_staff()`, matching `review_report()`'s own boundary
exactly. That required one more migration
(`202608270009_admin_moderation_visibility.sql`): nothing previously let
an admin actually *see* a reported "followers"-only post from a stranger
they don't follow, so `post_visible_to_viewer()` and a new
`workout_posts` RLS policy grant a real-admin-only bypass (deliberately
not `is_staff()`, which would have also handed every coach read access to
private posts they have no way to act on). Also caught and fixed while in
here: `COMMUNITY_SETUP.md`'s migration list had silently skipped
`202608270008_hebrew_handles.sql` since it shipped.

**Community UI pass.** Feed posts and comments now show an avatar (colored
initials, deterministic per person) and a relative timestamp ("לפני 3
שע׳") instead of just a name with no sense of who or when. Feed post cards
got a real header instead of a bare name line; the Account tab shows a
red badge with the open-report count so an admin sees at a glance whether
anything needs attention.

203/203 tests pass.

# Fix incomplete dark-mode contrast fix, found while auditing "what's left" — 2026-08-27

The rescan report flagged this correctly: an earlier accessibility pass
(the `--steel` contrast fix, WCAG AA) updated the auto-detected dark
theme (`@media prefers-color-scheme: dark`) but missed the explicit
`[data-theme="dark"]` block — a separate, textually-identical-looking CSS
rule that never actually got touched. Since `theme-init.js` stamps
`data-theme="dark"` by default for every existing user, the *explicit*
block is the one that actually matters for almost everyone, and it kept
shipping the old, contrast-failing value the whole time. Fixed by
re-checking directly rather than trusting the earlier commit message.

New test (`test/theme-token-parity.test.mjs`) locks in that every color
token in one dark-theme block matches the other, not just that both
blocks exist — the exact class of mistake that let this slip through
undetected.

192/192 tests pass.

# Allow Hebrew handles — this is a Hebrew-speaking app — 2026-08-27

Reported directly, with a screenshot of a Hebrew keyboard: the handle
field only accepted English letters (`a-z0-9_`), forcing a Hebrew-
speaking membership to switch keyboards and think up an English name
just to finish their profile. Widened both the database CHECK constraint
and the matching client-side regex to also accept Hebrew letters (א-ת),
same length bound (3-24) and same ban on spaces/punctuation as before —
still a compact identifier, not free text (`display_name` already covers
full free-form names).

Also fixed something the regex change alone would have left broken: both
handle inputs forced `dir="ltr"`, which would render Hebrew text
backwards while typing even once it was allowed. Switched to `dir="auto"`
so the field adapts to whichever script is actually typed into it.
Placeholder text updated to a Hebrew example (`דנה_כהן`) so the new
capability is obvious, not just technically possible.

3 new tests. 191/191 pass; visually verified — a Hebrew handle now renders
correctly, right-to-left, while typing.

# Fix two real bugs found by actually using the new sign-in flow — 2026-08-27

Reported directly: member search "not working," and no way to tell
whether a profile had actually been saved.

- **Member search only fired on blur.** `afterRenderCommunity()` bound
  the search box with a `"change"` listener — only fires when the field
  loses focus, not while typing. Every other search box in the app
  (`historySearch`) already uses a live `"input"` listener; this one just
  didn't match. Typing a name and seeing nothing happen, with no visible
  reason why, reads exactly like "broken."
- **A freshly-redeemed invite code landed on the mostly-empty Feed tab**,
  with the actual profile-creation form buried in the Account sub-tab and
  no cue pointing there. Someone who didn't know to navigate there could
  easily believe they were "done" without ever having created a profile
  at all — there was no way to tell "did this save?" from that screen.
  Fixed the same way the two gates before it already work (no session yet
  / no redeemed code yet): a signed-in, code-redeemed user with no
  profile now sees *only* a profile-completion form, full stop, until
  they save one — the whole screen changing to the real tabbed UI
  afterward is the confirmation, not a toast easy to miss.

2 new tests. 188/188 pass; both fixes visually verified against a mocked
client — the gate correctly blocks the tabbed UI until a profile exists,
correctly clears once one's saved, and search now fires from typing
alone with no blur needed.

# Remove email from community sign-in entirely — anonymous auth, invite code only — 2026-08-27

Sign-in no longer collects an email address or sends a magic link.
Opening the Community tab now silently creates a real Supabase Auth
session via `client.auth.signInAnonymously()` — a genuine `auth.users`
row, `auth.uid()` works normally, every existing RLS policy applies
exactly as before (anonymous sessions carry `role: authenticated` with
an `is_anonymous: true` JWT claim, not a lesser access level). The
invite code remains the only real gate — unchanged, still enforced
server-side by `profiles_insert_self`'s RLS policy at profile-creation
time, not by how the session was created.

Why: a magic-link email often opens in whatever the phone's default
browser is, not inside the already-installed home-screen PWA — the auth
session lands somewhere other than where the person meant to be. With no
email step at all, there's nothing to hand off to the wrong app.

Real tradeoff, not free: there's no "sign back in" path anymore — nothing
external ties a person to their identity, so clearing site data or
switching devices means a fresh anonymous session with no memory of the
old one, and the previous profile/history/streak becomes unreachable.
The Account tab's "sign out" button was removed for exactly this reason
— it would have implied a reversibility that doesn't exist; "request
account deletion" is still there for someone deliberately walking away.
The admin-grant instruction in `COMMUNITY_SETUP.md` also had to change
from an email lookup (`where email = ...`, meaningless now — anonymous
users have no email at all) to `where handle = ...`.

4 new tests in `test/community-anonymous-auth.test.mjs`. 185/185 tests
pass; boot-smoke passes with zero console errors against the live
project (Anonymous Sign-ins isn't enabled there yet — the failure path
was verified to degrade to a message, not a crash); visually verified
the connecting state via a mocked client, including that
`signInAnonymously()` fires exactly once per load even across repeated
re-renders and tab switches.

# Catch-up entry: security hardening, DevOps, and accessibility batches not logged here at the time — 2026-08-27

Three rounds of work landed as commits without a matching entry in this
file — recorded here after the fact so the history stays complete.

**Security hardening** (`202608270006_security_hardening.sql`, authored
by a separate Codex-based session working in this same repo, merged in
and then fixed through three live-testing rounds here): invite codes are
now hashed (never stored plaintext), high-entropy (48 hex chars),
expiring, bounded to a max redemption count, and rate-limited (5 attempts
per 15 minutes); coach promotion moved from a redeemable code to a
trusted `grant_coach_role()` service-role-only function; post photo paths
are bound to their author by a database trigger, with a 20-photo upload
quota; reports gained a real admin-only `review_report()` transition
instead of just hiding a post for its reporter; `is_staff()` no longer
accepts an arbitrary user id. Fixed afterward, in order, from live
`SQL editor` failures: a primary-key/foreign-key creation-order bug, a
`CREATE OR REPLACE FUNCTION` default-parameter removal Postgres
disallows, an RLS-policy dependency-ordering bug, and unqualified
pgcrypto calls that broke under the functions' own `search_path = ''`
hardening.

**DevOps**: `run-all.mjs` now auto-discovers browser-check scripts from
disk instead of a hand-maintained list that had silently excluded three
of them; running the full suite for the first time surfaced two scripts
that had gone genuinely stale against the app's current behavior
(unrelated to this work) and both were fixed. CI now runs the real-
Chromium browser suite as a required job, not just unit tests;
`actions/checkout`/`actions/setup-node` pinned to their exact current
commit SHAs; a concurrency group cancels superseded runs. The service
worker's install handler now fails outright if a *required* app-shell
file (index.html/app.js/theme-init.js/cloud.js) can't be cached, instead
of silently activating a broken shell the way every asset used to be
treated.

**Accessibility**: `:focus-visible` widened from `button, input` to
every interactive element type; `.footer-note`/`.link-btn` were using a
border color as text color, measuring under WCAG AA — fixed, and
`--steel` itself retuned per theme to clear 4.5:1 with real margin
everywhere it's already used as secondary text app-wide; two undersized
touch targets (the numeric-field +/- buttons, calendar month navigation)
brought up to 44×44px; the community photo picker gained real visible
label text instead of an emoji-only, title-attribute-only button; and a
real bug — a document-level focus handler was wiping every numeric
field's value the instant it was focused — fixed to select the existing
value instead (typing still replaces it in one keystroke, but the value
is never destructively cleared just from focusing).

# Build the coach access tier — 2026-08-27

Three real tiers now, via new migration `202608270005_coach_tier.sql`:
**admin** (unchanged — full access, manual dashboard-only grant),
**coach** (new — a fixed set of powers, the same for every coach: post/
pin announcements, set the weekly challenge, see the new/inactive member
views), **member** (the default).

Coach is deliberately *not* scoped to "their own" classes or members —
Arbox already owns class scheduling and rosters, so building a parallel
membership model here would duplicate something that already exists
elsewhere. This is the direct outcome of asking, now that Arbox is in the
picture: coach doesn't need a data model for "relevant," it just needs a
fixed set of community-layer powers.

Both tiers are checked server-side through one new function,
`public.is_staff()` (true if either `profiles.is_admin` or the caller's
own `invite_redemptions.role = 'coach'`) — every RLS policy and RPC that
used to check `is_admin` directly now goes through it, so "who counts as
staff" is defined in exactly one place instead of two policies that could
quietly drift apart over time. `cloud.js` got the matching client-side
`isStaff()` helper, and the render function's local `isAdmin` variable
(now genuinely misleading — it gated coach-relevant sections too) was
renamed to `staff` throughout.

6 new tests across `test/community-coach-tier.test.mjs` (migration
static assertions, plus one asserting the four staff-gated render
sections all route through `isStaff()` and none of them check
`state.profile.is_admin` directly anymore) and an update to an existing
engagement test whose assertion had gone stale. 164/164 tests pass;
boot-smoke passes with zero console errors.

# Fix the admin-grant trigger bug, and build the community-strategy quick/medium wins — 2026-08-27

## Bug: the manual admin grant never actually worked

`protect_is_admin` (from the previous migration) fired on every update to
`profiles`, unconditionally resetting `is_admin` back to its old value —
including for a legitimate `update ... set is_admin = true` run directly
in the SQL editor. The trigger doesn't know or care who's running the
UPDATE, only that a row changed, so it silently undid the grant every
time — `is_admin` stayed `false` no matter how many times the manual step
was followed correctly. Fixed by scoping the trigger to `auth.role() =
'authenticated'`: real client requests always carry a JWT and read
`'authenticated'` from it, while a direct SQL editor session has no JWT
context at all and reads `null` — so the trigger now only clobbers the
column for actual client requests, exactly the property it was meant to
have, while a genuine dashboard-run grant now works.

## New migration: `202608270004_community_engagement.sql`

Built from a strategy review of what makes fitness-app communities work
(Strava, Peloton, Duolingo, SugarWOD/Wodify) against what this app
actually has — the quick wins and medium bets from that review, not the
bigger one (class scheduling), which still needs its own planning pass.

- **Comments** — `post_comments`, gated by the same `post_visible_to_viewer()`
  rule reactions already use, so a comment can never be more exposed than
  its post. `community_feed` gained a `comment_count` alongside
  `cheer_count`.
- **"Who's new"** — `coach_new_members()`, the mirror of
  `coach_inactive_members()`: same admin self-gate, but looks at each
  member's *earliest* `activity_pings` row instead of their latest.
- **Photo attachment** — one optional photo per shared result. A private
  `post-photos` Storage bucket (5MB limit, image MIME types only),
  RLS-scoped so uploads only ever land under the uploader's own
  `uid/...` folder, and read access mirrors the post's own visibility
  rule rather than defaulting to public or owner-only.
- **Pinned daily note** — `announcements.pinned_date`; when set to today,
  it surfaces as a distinct "today's workout note" instead of sitting in
  the regular chronological list.

## Community tab: sub-tabs, top-3-plus-your-rank, comments UI

`cloud.js`'s render function was rewritten around three sub-tabs (Feed /
Boards / Account, reusing the same `.subtabbar` pattern the WOD tab
already has) instead of one long scroll through profile, announcements,
weekly challenge, streaks, member search, sharing, the feed, and the
admin views, all stacked vertically.

Streaks and the weekly challenge now render as top-3-in-full, then — if
the viewer isn't already in the top 3 — a divider and their own
highlighted row, instead of one long ranked list past the leaders
(showing someone they're "#18 of 40" discourages more than it motivates;
a small, friendly comparison does the opposite).

Each feed post gets a comment count/expand button alongside the existing
cheer count; expanding loads and shows the thread plus a small
add-a-comment form, and a comment's own author gets a delete link on it.
Sharing a result now offers an optional photo attachment via a
lightweight `<label for=...>` file-picker trigger next to the existing
followers/public buttons.

13 new tests across `test/community-engagement.test.mjs` (migration
static assertions) and `test/community-engagement-ui.test.mjs` (source
shape of the new render/wiring). Visual behavior verified with real
screenshots against a mocked Supabase client (a real signed-in session
isn't reachable without a live magic-link email) — all three sub-tabs,
the expanded-comments state, and the ranked-list framing. 157/157 tests
pass; boot-smoke browser check passes with zero console errors against
the live (partially-migrated) backend.

# Redesign the Community tab — it was misusing the app's own design system — 2026-08-27

Every section of the Community tab (profile, announcements, weekly
challenge, streaks, member search, feed) rendered as an identical stack of
`.chart-card` boxes separated only by a tiny 12px gray `.section-label`,
with almost every action — save profile, follow, block, cheer, report,
post an announcement, set the weekly challenge — using `.link-btn`. That
class is an 11px underlined micro-link, styled in `var(--border)` (the
lowest-contrast color in the palette), meant for a deliberately
de-emphasized action like "delete account." Using it for every primary
action in the tab is what made the whole screen read as a flat, low-
contrast wall of near-identical boxes with no hierarchy.

Fixed by reusing the app's own existing vocabulary instead of inventing a
new one: every section now gets a real header — the same colored-dot +
bold-title pattern (`.ach-section-head`/`.ach-section-dot`/
`.ach-section-title`) the achievements screen already uses, one accent
color per section (brass for announcements, teal for the weekly
challenge, purple for streaks, energy for sharing, blue for the feed and
comparisons, red for the admin-only inactive-members view) so sections
are visually distinguishable at a glance, not just by reading the label.

New `.chip-btn`/`.chip-btn.primary`/`.chip-row` give every real action an
actual button (bordered chip for secondary actions, filled energy-orange
for the primary one per group) instead of underlined micro-text — `.link-btn`
now only used where it already made sense, the account-deletion link.

Admin-only forms (the announcement composer, the weekly-challenge setter)
now get a visibly distinct treatment — an energy-orange left border
(`.admin-card`) plus a small "ניהול" pill (`.admin-tag`) right on their
heading — so it's unmistakable which controls are admin-only versus
regular community actions, which the flat card stack made impossible to
tell apart before. The profile form also gained real field labels above
each input instead of relying on placeholder text that disappears the
moment a value is set.

Verified visually, not just by reading the diff: screenshotted the tab
against realistic mocked data (a fake Supabase client stubbed in before
page load, since a real signed-in session isn't reachable without a live
magic-link email) before and after — the "before" shot is what surfaced
this in the first place. 145/145 tests and the boot-smoke browser check
still pass.

# Gate community sign-up behind an invite code, and fix an admin self-lockout bug found along the way — 2026-08-27

Anyone who found the demo URL could sign in with any email and create a
community profile. New migration `supabase/migrations/202608270003_invite_gate.sql`
closes that: `invite_codes` (one shared code per role, member/coach) plus
`invite_redemptions` (one row per user, written only by the new
`redeem_invite_code()` RPC — no direct client insert path). `profiles_insert_self`
now requires a redemption on file before a profile can be created at all.
Community tab shows a new "enter invite code" step ahead of the profile
form whenever a signed-in user hasn't redeemed one yet.

The end state discussed for this is three access tiers — admin (full
access), coach (scoped to their own relevant classes/members), member —
but "coach" doesn't have a data model for what "their relevant" means
yet. So a coach-code redemption is deliberately just a label right now
(`invite_redemptions.role`), not wired to `is_admin` or any elevated
access — avoids locking in "coach == full admin" as the real design
before the actual scoping work happens. Full admin stays a manual,
dashboard-only grant, same as before this migration.

Bug found while writing the above: `profiles_update_self`'s RLS check
required `is_admin = false` on *every* update — meaning the moment any
profile actually had `is_admin = true`, that account could never save its
own profile again (any edit would get rejected, since the resulting row
still has `is_admin = true`). This would have locked out the very first
real admin account. Fixed with a trigger (`protect_is_admin`) that pins
`is_admin` to its previously stored value on every update, so no
client-side path — invite code, profile-edit upsert, or otherwise — can
ever change it after creation; the update policy's `is_admin = false`
requirement was then unnecessary and removed.

5 new tests in `test/community-invite-gate.test.mjs`. 145/145 pass.

# Lock down an anon read leak found by live-testing the previous migration — 2026-08-27

Found immediately after applying `202608270001_community_growth.sql`
against the live project and testing it with no login at all (just the
publishable key, no session): `activity_pings`, `announcements`,
`weekly_challenges`, and the `community_streaks` view were all readable
by anyone, no auth required. `activity_pings` in particular was designed
to be self-only — its own RLS policies say so — but RLS never got a
chance to run, because the `anon` role had a standing table-level SELECT
grant that bypassed the question entirely. Writes were still safe: a test
insert into `announcements` correctly failed on the RLS policy.

Cause: this Supabase project has a default privilege that auto-grants
`anon` (and `authenticated`) SELECT/INSERT/UPDATE/DELETE on any newly
created table. `202608260001`'s blanket `revoke all ... from anon,
authenticated` only covered tables that existed at the moment it ran —
every table `202608270001` created afterward silently picked the default
back up, since nothing in that migration re-revoked it.

New migration `202608270002_lock_anon_defaults.sql`: revokes the leaked
access on the four objects above, and — so this can't repeat itself the
next time a migration adds a table — runs `alter default privileges in
schema public revoke select, insert, update, delete on tables from anon,
authenticated`, which stops the auto-grant from applying to anything
created from this point forward. Every table this app needs already gets
an explicit `grant ... to authenticated` alongside its own RLS policy, so
nothing legitimate depended on the default.

1 new static-assertion test locks in that this migration exists and does
what it says.

# Close the reactions RLS gap, and add achievement sharing, streaks, announcements, and a weekly challenge — 2026-08-27

Two threads from the earlier audit of this repo's community layer, done
together: closing out the remaining credibility gaps it found, and
building the growth features discussed for pitching this to the box
manager.

## Credibility fixes

- **CSP `frame-ancestors`**: the audit flagged this directive as dropped
  compared to a "proper" CSP. On inspection this isn't fixable as stated —
  `frame-ancestors`/`X-Frame-Options` are spec-ignored when delivered via
  `<meta>`, only a real HTTP response header enforces them, and GitHub
  Pages has no way to set custom response headers on static files. Adding
  the directive back to the `<meta>` tag would be inert, not a fix. Left
  the file's own comment expanded to say this plainly instead of silently
  re-adding dead config — real clickjacking mitigation here would need
  moving off GitHub Pages. For what it's worth, the production app ships
  no CSP at all, so this demo is still strictly ahead on every directive
  that *does* work via `<meta>`.
- **Reactions RLS gap**: `reactions_visible`/`reactions_insert_self` only
  checked that the referenced post *existed*, not that it was still
  visible to the viewer — a deleted post, a blocked author, or a
  followers-only post from someone you don't follow all leaked reaction
  rows even though `posts_feed_select` correctly hid the post itself. New
  migration factors the exact visibility rule `posts_feed_select` already
  uses into `post_visible_to_viewer()` and both reaction policies now call
  it, so the two rules can't drift apart again.
- **README.md**: rewrote it — it still described the old mock-data-only
  preview ("runs entirely on mock data today... not live for real
  members"), which stopped being true once this became a real
  Supabase-backed PWA.

## New features

New migration `supabase/migrations/202608270001_community_growth.sql`
(on top of the existing `202608260001_community_foundation.sql` — **must
be run against the live Supabase project before these features work; this
session had no CLI/service-role access to apply it directly**):

- **Achievement-unlock sharing**: `workout_posts.source_type` now accepts
  `'achievement'` alongside the existing strength/WOD entry types. A new
  share button appears per newly-earned badge directly in the existing
  celebration popup (`celebrationShare` in `index.html`, wired in
  `showCelebration()` in `app.js`) — only when the community layer
  reports the athlete signed in (`window.isCommunitySignedIn()`).
  Achievement unlocks aren't durable local records the way strength/WOD
  entries are, so this is a transient share offer at the moment of
  unlock rather than an addition to `communityShareCandidates()`.
- **Activity streaks**: new `activity_pings` table (one row per user per
  day, self-insert/self-select only — raw per-day presence stays
  private) plus a `community_streaks` view that aggregates a
  gaps-and-islands current-streak calculation across every user and
  exposes only the resulting number to the whole community. The view is
  deliberately *not* `security_invoker`, so it can read across
  `activity_pings` rows RLS would otherwise restrict to their own owner —
  the raw dates never leave the table, only the streak length does.
- **Coach announcements**: new `announcements` table, admin-only insert
  (checked against `profiles.is_admin`), readable by every signed-in
  member. Composer form appears in the Community tab only for admins.
- **Weekly box-wide challenge**: new `weekly_challenges` table (admin
  sets a title, a `comparison_key`, and a date range) plus a
  `weekly_challenge_leaderboard` view that reads straight from the
  existing `workout_posts` — reusing `posts_feed_select`'s visibility
  rules via `security_invoker`, so a challenge leaderboard never shows a
  post its own visibility settings would otherwise hide from that viewer.
- **Coach "who hasn't logged recently"**: new `coach_inactive_members()`
  function, security-definer with an internal admin check (raises if the
  caller isn't an admin profile) rather than widening `activity_pings`'
  own RLS — keeps raw per-day activity data admin-only without a second
  parallel table.

7 new static-assertion tests in `test/community-growth.test.mjs` (matching
the existing pattern in `test/community-foundation.test.mjs` — no live
Postgres to run migrations against in this test suite) plus 2 new
jsdom tests in `test/achievements.test.mjs` covering the celebration
share button's visibility and click wiring.

# Isolate this demo's browser storage from the production app — 2026-08-27

Found by an independent audit: this demo and the real production app
(`haimuniya.github.io/haimunia-app/`) are served from the same GitHub
Pages origin — just different paths — and browser storage (IndexedDB,
localStorage, sessionStorage, Cache Storage) is scoped per-origin, not
per-path. This demo was using the production app's exact identifiers:

- IndexedDB: `DB_NAME` was `"box-log-db"`, identical to production.
  A real member whose browser had opened both URLs would have this
  demo's community/social code reading and able to publish their real
  local training data.
- localStorage/sessionStorage: every key used the bare `"haimunia:"`
  prefix (or the legacy `"boxlog:"` one), same as production.
- Cache Storage: the service worker's cache name shared production's
  `"haimunia-v..."` prefix — and its activate handler deleted *any*
  cache that wasn't its own current version, which would have deleted
  the production app's cached assets outright the first time both
  service workers had ever run in the same browser.

Every identifier above is now demo-specific (`"haimunia-demo-db"`,
`"haimunia-demo:*"` keys, `"haimunia-demo-v..."` cache names), and the
service worker's cleanup now only ever deletes caches matching its own
prefix instead of "anything that isn't me." `manifest.json`'s `id`/
`start_url`/`scope` were checked too — those are relative URLs that
already resolve differently per path, so no change was needed there.

4 new tests in `test/storage-isolation.test.mjs` lock this in: the
IndexedDB name, every storage key actually written during real app
flows, a source-level sweep of all four JS files for any lingering
production identifier, and the cache-cleanup scoping logic itself (not
just its name). Full suite: 130/130 (126 existing + 4 new), green.

# Fix: WOD tab's רישום/היסטוריה pill highlight not following the subtab — 2026-08-25

Reported by the user with a screenshot: after switching WOD subtabs,
היסטוריה stayed highlighted while the רישום (log) form was actually
showing underneath. Root cause: the pill buttons are rendered once in
renderWodTab(), which only runs on a full top-level tab switch —
switch-wod-subtab's handler only ever called renderWodContent() (swaps
#wodContent's innerHTML), so the content switched correctly but the
highlight never followed it. Fixed by having the handler also update the
two buttons' active/aria-selected state directly, same pattern already
used for the WOD builder's format chips.

# Workout format support, sub-tasks A (WOD builder half) + B + D + extras — 2026-08-25

Finishes the workout-format-support spec: the WOD builder's own duration
toggle (the other half of sub-task A), blocks/supersets (B), EMOM (D), and
the two lower-priority extras (time cap, partner tag). Sub-task C was
already covered by the existing ladder feature (confirmed in the previous
round). Plain single-exercise logging, and every previously-shipped
feature, is unaffected — re-verified via the full test suite and browser
checks after each addition below.

- **WOD builder duration toggle.** A movement checked in the builder can be
  marked "reps" or "duration" (a reps/duration chip pair per movement,
  reusing the toggle from the Log tab). Only changes the free-text
  description the builder generates (`builderMovementsToDesc`) — WOD
  entries themselves have never stored structured per-movement data for any
  format except EMOM (see below).
- **Supersets and A/B/C/D block labels.** Extends the existing ladder
  mechanism rather than replacing it: a ladder can now optionally take a
  second exercise (`setLadderPartner`), turning it into a superset —
  alternating rounds between exactly two exercises under one `groupId`,
  switched between via two pills (`switchLadderExercise`) instead of the
  normal exercise picker (which still ends it, same as before). An
  optional `blockLabel` chip (A/B/C/D) tags the whole group, carried by
  every round. The calendar day view and Log tab's running list both
  derive "is this a superset" from the group's own data (more than one
  distinct exerciseId), not from in-progress session state, so a finished
  superset displays correctly regardless of how it was built.
- **EMOM.** A fourth WOD scoreType, built through the same
  reusable/named WOD builder as Fran or Grace — not a one-off freeform
  entry. Unlike every other format, an EMOM's movement rotation
  (`emomMovements`/`emomTargetReps`/`emomMinutes`) is structured data on the
  WOD record itself, because the log form needs it to render one reps
  field per movement, prefilled from that WOD's own targets and resized
  automatically when switching between differently-shaped EMOM WODs.
  Explicitly out of scope per the confirmed spec: no cross-attempt scoring
  — `bestWodScore`/the History tab's PR chart both skip EMOM entirely
  rather than fabricate a comparison that doesn't mean anything for it.
- **Time cap and partner tag.** Two small, independent additions: an
  optional reference-only time cap on a WOD (shown in the log header,
  never enforced or scored), and a free-text partner tag per WOD entry
  ("with Dana") shown next to Rx/Scaled in history and the calendar.

Also fixed along the way: the strength Log tab's est-1RM/barbell-visual
live-update on raw keystroke input wasn't duration-mode-aware (a latent gap
from the previous round, caught while wiring the same live-update path for
the new duration stepper), and picking an exact-name search match in the
exercise picker via Enter didn't end an active ladder the way clicking the
same movement's button already did — both now consistent.

# Workout format support, sub-task A: duration/hold entries — 2026-08-25

A structured spec came in covering four workout-logging gaps that BTWB/
SugarWOD-style apps handle poorly: timed holds, multi-part A/B/C blocks
with supersets, pyramid rep schemes, and EMOMs with rotating movements.
Pyramid schemes turned out to already be covered by the existing ladder
feature (confirmed, not assumed — skipped as its own sub-task). This round
covers sub-task A only; blocks/supersets and EMOM are separate, larger
changes staged for their own rounds.

- **Duration/hold entries in the strength Log tab.** A new reps/duration
  toggle next to the exercise picker switches the whole entry form: reps
  mode is exactly what existed before (unchanged), duration mode swaps the
  reps stepper for a duration-in-seconds one and skips the barbell-plate
  visual and bar-weight row (neither applies to a timed hold). Weight stays
  available in duration mode for weighted carries/holds, defaulting to 0
  for a bodyweight hold. `sanitizeEntry` gained a `type` ("reps" |
  "duration") discriminator and a `durationSeconds` field — every entry
  from before this change has no `type`, which sanitizes to "reps"
  automatically, so existing data and the plain reps flow are unaffected.
- Selecting an exercise now defaults the toggle to whatever it was last
  logged as (a hold-only movement like a plank stays in duration mode),
  and editing an existing entry restores its own type regardless of
  whatever the toggle currently shows.
- PR tracking, the History tab's per-exercise chart, and the achievement
  system's per-category PR counter all now correctly separate duration
  entries from reps entries — a hold-only movement reports "no 1RM" (not a
  phantom 0kg one), and its History chart plots hold time instead of
  est1RM. Recent-history, the calendar day view, and ladder-round display
  all format each entry by its own type, so a mixed history (an exercise
  logged both ways over time) renders correctly everywhere.
- Ladders and duration entries compose: a ladder can be a sequence of
  progressively longer holds, same as it can be a sequence of different
  weight/rep rungs. Switching the reps/duration toggle mid-ladder ends it,
  same as switching exercise or date already did.

# Roadmap round: notifications, onboarding, streaks, recent history, session notes — 2026-08-25

A 10-phase roadmap came in for "look at every tab." Two phases turned out
to already be substantially satisfied by existing code (found during
research, not assumed): the WOD tab's custom + Girls/Heroes-benchmark entry
paths, and the Log tab's last-session reference (which the immediately
preceding round had already turned into a tap-to-prefill button). Phase 9
depended on a "Goals" feature that doesn't exist anywhere in the codebase —
asked directly, skipped for this round. Phase 8 (build-then-commit a whole
session before saving anything) is a real redesign of the save flow the
user themselves flagged as needing its own planning pass — deferred to a
dedicated follow-up rather than bundled in with seven other features.

This round: expanded `WOD_LIBRARY` with 7 more evergreen benchmarks (Kelly,
Eva, Barbara, Filthy Fifty, Michael, Danny, Badger). Everything below is new.

- **Update notifications.** A small `RELEASE_NOTES` list (separate from
  this file — short, Hebrew, user-facing) backs both a one-time "מה חדש"
  popup shown to returning users after a real update, and a persistent bell
  icon in the header with an unread badge. A genuinely fresh install sees
  neither — nothing to catch up on; existing devices from before this
  shipped get silently backfilled so they're never shown a changelog
  retroactively.
- **First-time onboarding.** A short one-screen walkthrough (what each tab
  is for) shown once, immediately after the very first welcome/name modal —
  never for a device that already has data or a name.
- **Recent history at the point of entry.** Picking an exercise or WOD now
  shows up to 5 real logged attempts from the last 14 days, not just the
  single most-recent one. No warm-up logic anywhere in it — every row is an
  actual saved set.
- **Streak indicator.** Consecutive days (strength set or WOD, either
  counts) with at least one entry, shown next to the header's date. Reuses
  the exact same day-has-an-entry check the calendar's dots already used
  (extracted into one shared `hasAnyEntryOn`), so the two can never disagree
  about what counts as a trained day. Today not being logged yet doesn't
  break it — just isn't counted until it is.
- **Per-day session note.** One free-text field per calendar date ("how did
  the session feel"), distinct from the existing per-WOD-entry scaling
  notes. Surfaced from the Calendar day view.

Files changed: `app.js`, `index.html`. New `test/roadmap-features.test.mjs`
(7 tests: version comparison, fresh-install vs. existing-device bootstrap
paths, streak counting across gaps, the 14-day/5-item recent-history cap,
session-note round-trip). New `scripts/browser-check/roadmap.mjs` — real
Chromium session driving all five features end to end, including the
session note surviving a navigate-away-and-back round trip. `boot-smoke.mjs`
and `ladder.mjs` re-verified for regressions; their shared `dismissWelcomeModal`
helper updated to also close the new onboarding modal, since every
fresh-context check now hits it.

---

# Prefill from last session — 2026-08-25

Reframed what this app actually is: filled in after a workout (from memory
or a whiteboard scribble), not used live during one — which rules out
things like a rest timer, but means entry *speed* for reconstructing a
session is what matters. Progressive overload means today's numbers are
usually close to last time's, not random, yet the "אימון אחרון" (last
session) card was informational only — you still dragged the steppers from
scratch every time.

It's now a button: tapping it copies that exercise's last weight, reps,
and sets straight into the steppers (and the barbell visual updates with
them). A small repeat icon signals it's interactive, distinct from the
adjacent 1RM card which stays informational.

Files changed: `app.js`. Two new tests in `test/app-flow.test.mjs` (prefill
pulls the right exercise's history, not whatever was left over from a
different one; no-op when there's no history yet). Verified visually in a
real Chromium session — steppers and barbell both update from one tap.

---

# Committed browser-check scripts — 2026-08-25

Three real bugs this session (self-reload on first install, PR celebration
firing on every ladder rung, editing mid-ladder not ending it) only
surfaced through real-Chromium testing — jsdom doesn't implement Service
Worker lifecycle or real DOM event timing, so the committed `npm test`
suite structurally can't catch this class of bug. Those checks previously
lived as scratch scripts, rebuilt from scratch each time.

`scripts/browser-check/` — a separate package (own `package.json`, own
`playwright` dependency, own lockfile) so the main app's dependency tree
stays untouched:

- `npm run setup` once (installs Playwright + downloads Chromium)
- `npm run check:boot` — fresh load, fonts actually loaded, no self-reload,
  all 4 tabs switch, no console errors
- `npm run check:ladder` — a real 5-round working-up ladder end to end:
  toggle, save, celebration suppression, calendar grouping, edit, delete,
  finish
- `npm run check:update` — the Service Worker update lifecycle (first
  install doesn't self-reload; an update hidden from view auto-applies
  silently; one landing mid-session shows the banner and applies on the
  next visibility regain). Local-only — it edits `sw.js` on disk to
  simulate a new deploy landing, reverted when it's done.
- `npm run check:all` runs all three, stopping at the first failure

Each defaults to a throwaway local static server over the working tree
(uncommitted changes included); `TARGET_URL=<url>` points any of them at a
deployed site instead, e.g. to verify a push actually landed.

Not part of the main test suite or any CI — on-demand only, the same way
this session ran them by hand throughout.

---

# Gap-hunting pass — 2026-08-25

Went back through the app looking for rough edges, focused on the ladder
feature since it's newest. Found and fixed one real interaction bug, plus
an accessibility gap.

- **Bug: editing an unrelated entry mid-ladder didn't end it.**
  `startEditEntry()` (the pencil icon on any set in history/calendar)
  switches the selected exercise and log date, exactly like picking a new
  movement or changing the date already did — but unlike those two, it
  never called `endLadder()`. Editing an old set from a different exercise
  while a ladder was running left the toggle still advertising an active
  ladder for the wrong context. Fixed — with one deliberate exception:
  editing one of the *active ladder's own* rounds (fixing a typo in set 3)
  does **not** end it, so correcting a mistake mid-session doesn't strand
  you from adding set 6 afterward.
- **Accessibility:** the ladder progress text ("5 סטים נרשמו · הבא: 6")
  now carries `aria-live="polite"`, matching the pattern already used for
  the storage-error and import-result messages.

Files changed: `app.js`. Two new regression tests in `test/app-flow.test.mjs`
cover both the "unrelated edit ends it" and "own-round edit doesn't" cases;
the fix was verified in a real Chromium session too — my own test script
had exercised this exact path without realizing the tested behavior was
wrong until this pass looked closer.

---

# Ladder UX pass — 2026-08-25

The ladder toggle worked but was easy to miss (a small text link) and gave
no feedback on what it actually did — no indication of which set you were
on, the save button never changed to reflect it, and finishing without
switching tabs first left stale state on screen (a real bug: `endLadder()`
via the explicit toggle never called `render()`, so the UI kept showing
"finish ladder" and the old round list until something else happened to
re-render).

- Toggle is now a full-width bordered button (matching the app's existing
  "+ add new" prompt pattern) with a ladder icon and a plain-language
  subtitle when off. While active, it shows live progress inline — "5 סטים
  נרשמו · הבא: 6" — instead of requiring a scroll down to the chip list to
  know where you are.
- The Save button's own label now changes too: "הוספת סט 6 לסולם — Strict
  Press" instead of the generic "רישום סט", so it's explicit that tapping
  it adds another rung rather than finishing anything.
- Fixed: tapping "סיום" now re-renders immediately (previously required
  switching tabs to see the toggle/list actually clear) and shows a brief
  confirmation ("הסולם נשמר — 5 סטים") reusing the existing footer message
  mechanism.
- Fixed a copy bug: the empty-ladder hint referenced "the blue button" —
  the save button is actually the brand's orange/energy color, never blue.

Files changed: `app.js`. Verified with the full test suite plus a real
Chromium session driving the exact flow (toggle on, 5 different-weight
rounds, finish without switching tabs, confirm the render and message).

---

# Service worker: stop self-reloading on first install, apply updates without reopening — 2026-08-25

Two bugs in the update-delivery path, found while chasing a report that the
new ladder feature "wasn't showing up."

**Critical: every fresh visit was reloading itself ~1-2s after opening.**
`self.clients.claim()` in the service worker's `activate` handler fires
`controllerchange` even on a page's very first-ever install — not just on a
real update swap. The app's `controllerchange` listener reloaded
unconditionally, so any in-progress input (the welcome-modal name field, a
weight being adjusted, a ladder mid-session) could get silently wiped a
second or two into every single visit. `applyUpdate()` now sets a
`swapRequested` flag right before asking a waiting worker to take over, and
the listener only reloads when that flag is set — ignoring the incidental
first-claim event. Confirmed via a real Chromium session: before the fix, a
fresh load always fired a second navigation within ~2s; after, zero.

**Updates now apply without a manual reopen, in the common case.** Previously
every update needed an explicit tap on the "עדכון חדש זמין" banner. Since the
phone screen locking between sets already fires `visibilitychange`, updates
now apply automatically the moment the page regains visibility after being
backgrounded — no banner, no reopening needed. The banner still appears as a
fallback only when an update lands while the page has stayed continuously
visible (reloading then could drop unsaved input), and applies automatically
on the next visibility regain even if the banner is never tapped.

Files changed: `app.js`. No test suite coverage for either fix — both are
real Service Worker lifecycle behavior that jsdom doesn't implement, so they
were verified with a real Chromium session (Playwright) against a local
static server instead; see the session's own scratch scripts for the pattern
if this code changes again.

---

# Ladder logging — 2026-08-25

Working-up ladders (e.g. Press: 6 reps @ 60, 5 @ 70, 4 @ 80, 3 @ 85, 3 @ 90 —
each rung a different weight *and* rep count) didn't fit the "Sets" field,
which only means "N identical sets at one weight/reps." Saving each rung
separately already worked, but showed up as unrelated rows.

- Entries gained an optional `groupId` (`sanitizeEntry`) tying together the
  rows saved in one ladder session. Existing records get `groupId: null` —
  no behavior change for anyone who never uses this.
- New toggle in the log tab: "רישום סולם" turns it on (generates a session
  id), every Save while it's on joins that session, a running list of the
  rounds so far shows underneath with a per-round remove. "סיום סולם" turns
  it off. Switching exercise or changing the log date auto-ends it, so a set
  can't silently misjoin the wrong session.
- The calendar day view groups a ladder's rows into one card (exercise name
  + PR flame shown once) — but every rung keeps its own edit/delete, so a
  specific set stays individually correctable.
- The full-screen "PR!" celebration popup is suppressed while a ladder is
  active — an ascending ladder routinely beats the previous best est1RM on
  every rung, which meant one popup per rung. The inline barbell flash still
  shows a PR immediately; the popup resumes normally once the ladder ends.
- Nothing else changed: PR detection, `bestEst1RM`/`repRecordFor`, the
  progress chart, and export/import all still treat every round as its own
  entry, same as before — a ladder's rungs just happen to share a tag.

Files changed: `app.js`. Tests: `test/sanitizers.test.mjs` (groupId
round-trip), `test/app-flow.test.mjs` (a real 5-round ladder end to end,
including surviving a simulated reload, and exercise-switch auto-ending it).

---

# "Next level" pass — 2026-08-25

Follow-up to the review below: closed out the "left for you" items from the
2.8.0 pass, plus an accessibility sweep, an install prompt, and the first
committed automated test suite.

Files changed: `app.js`, `index.html`, `sw.js`. New: `assets/fonts/*` (13
files), `package.json`, `package-lock.json`, `scripts/sync-version.mjs`,
`test/*`, `.gitignore`. `manifest.json` unchanged.

Verified with `npm test` (Node's built-in test runner, jsdom + fake-indexeddb,
dev-only — nothing here ships to the deployed site): **19 assertions**, all
passing, covering sanitizers/XSS-escaping, the add-movement → log-a-set →
simulated-reload round trip, and the import path (valid backup, `__proto__`
category neutralization, wrong-app-id rejection, oversized-file rejection).

## Self-hosted fonts, tightened CSP

- Downloaded the exact Rubik (400/600/700/800/900, latin+hebrew subsets),
  JetBrains Mono (500/700), and Anton (400) `.woff2` files Google's own CSS2
  API serves for this app, into `./assets/fonts/`. Verified woff2 magic bytes
  on all 13 files.
- Replaced the Google Fonts `<link>` in `index.html` with local `@font-face`
  rules using the same `unicode-range` values, so subsetting behavior is
  unchanged.
- CSP's `style-src`/`font-src` no longer allow any external origin — the app
  now makes zero third-party network requests, full stop.
- `sw.js` precaches all 13 font files, so typography no longer degrades
  offline.

## Accessibility pass

Previously: 2 `aria-*`/`role` attributes in the whole app. Now: 120 across
`index.html` + `app.js`. Added:
- `role="tablist"`/`"tab"`/`aria-selected` on the main tab bar and the WOD
  sub-tab bar, kept in sync on every tab switch.
- `role="dialog"` `aria-modal` `aria-labelledby` on all 6 modals (picker, WOD
  picker, WOD builder, achievements, celebration, welcome), `aria-label` on
  every icon-only close button.
- `aria-label` on every search input, date input, and icon-only edit/delete
  button; `aria-label` on the stepper +/− buttons and value fields.
- `role="radiogroup"`/`"radio"` + `aria-checked` on the WOD format picker, bar
  weight picker, Rx/Scaled toggle, and theme picker; `role="checkbox"`
  `aria-checked` on the WOD-builder movement checklist rows.
- `role="status"`/`aria-live` on the update banner, install banner, loading
  screen, storage-error footer note, and import-result message.

## Version sync automated

`APP_VERSION` (app.js) and `SW_VERSION` (sw.js) were kept in sync by hand.
`scripts/sync-version.mjs` now does it — `npm run sync-version` after bumping
`APP_VERSION`, `npm run check-version` (or `npm test`) fails loudly if they
ever drift.

## Install prompt

Custom "Add to Home Screen" banner (`app.js`: `beforeinstallprompt` handling;
`index.html`: `#installBanner`), styled like the update banner but with the
brand stripe instead of solid energy color so the two are visually distinct.
Shows once per session, steps aside if an update banner is showing, never
shows if already installed. iOS Safari doesn't fire `beforeinstallprompt`, so
the banner simply never appears there — no regression, just no improvement
for that platform.

## Export privacy notice

One line under the export/import buttons: the backup file is plaintext JSON
and includes name, bodyweight history, and full training log.

## Left undone (by design, not oversight)

- **Server response headers** (HSTS, `X-Content-Type-Options`,
  `Permissions-Policy`, real `frame-ancestors`) — GitHub Pages can't set
  custom headers; would need Cloudflare or another host in front. Decided
  against for now: no backend, no data leaves the device, so this was already
  low real-world risk.

---

# Security & hardening pass — v2.7.0 → v2.8.0

Files changed: `app.js`, `index.html`, `sw.js`. `manifest.json` unchanged.

Verified with two suites run against the real app booted in a DOM
(jsdom + fake-indexeddb): **58 security assertions** and **59 functional
regression assertions**, all passing.

---

## Critical

### 1. XSS via unescaped HTML attributes
`esc()` was applied to text nodes but skipped on several attribute values.

- `renderStepper()` — `data-field`, `data-action`, `data-step`, `data-min`,
  `value`, and the label are now all escaped. `field` is a user-authored
  movement name from the WOD builder.
- `data-id` on `pick-movement`, `pick-wod`, `select-history`,
  `select-wod-history`, `delete-entry`, `delete-wod-entry`; `data-date` on
  `cal-select-day`.
- `CATEGORY_LABELS[cat] || cat` and `style="background:${CATEGORY_COLORS[cat]}"`
  — replaced with `catLabel()` / `catColor()`, which use `hasOwnProperty` and
  fall back to safe defaults, then escaped.
- The `render()` catch-block printed `err.message` raw into `innerHTML`.

The `id` and `category` sinks were reachable from an imported backup file,
which is the vector that mattered.

### 2. Import accepted arbitrary data
`importDataFromFile()` checked only that `record.id` was truthy.

- Added `sanitizeMovement` / `sanitizeCustomWod` / `sanitizeEntry` /
  `sanitizeWodEntry` / `sanitizeBodyweight`. Each rebuilds the record field by
  field from a whitelist: `cleanId` (charset `A-Za-z0-9._:-`), `cleanStr`
  (control chars stripped, length capped), `cleanNum` (clamped both ends),
  `cleanISODate`, `cleanTs`. Nothing from the file is ever stored as-is.
- `data.app` and `data.version` are now verified (they were written on export
  and ignored on import).
- 25 MB file cap, 20,000-record-per-list cap.
- Confirmation prompt before merging, and a `box-log-rollback-<date>.json`
  auto-backup is downloaded first, since the merge can't be undone in-app.
- Result message reports imported / rejected / failed-to-save counts.
- New `reloadFromDb()` re-sanitizes on every load, so records written by an
  older build of the app can't poison the render path either.

### 3. Prototype pollution → persistent DoS
`byCategory[m.category]` with `category: "__proto__"` resolved to
`Object.prototype`, and `.push` threw a `TypeError`. Because the record was
persisted, the picker crashed on every load until "clear all data".

- `byCategory` and `builderMovements` now use `Object.create(null)` via `bag()`.
- `catColor` / `catLabel` guard lookups with `hasOwnProperty`.
- The category whitelist in the sanitizer closes the entry point.

---

## Hardening

- **CSP added** to `index.html` — `script-src 'self'`, `object-src 'none'`,
  `base-uri 'none'`, `form-action 'none'`, `connect-src 'self'`.
  `'unsafe-inline'` is in `style-src` only (inline `style=` attributes; there is
  no inline `<script>` anywhere). `frame-ancestors` is in the meta tag but is
  ignored there — **set it as a real response header on the host.**
- `<meta name="referrer" content="no-referrer">`.
- Google Fonts left in place but documented inline with the exact steps to
  self-host; `preconnect` to `fonts.gstatic.com` was missing and is now added.
  Self-hosting is the one item I couldn't do for you — it needs the woff2 files.

---

## Service worker (rewritten)

- **Origin-gated.** It previously cached every successful GET from any origin,
  forever. Now same-origin only, and only app-shell paths are written back.
- **`Promise.allSettled` over individual `cache.add()`** instead of `addAll()`,
  which failed the entire install on one missing file.
- **Added the maskable icons** to `ASSETS` (referenced in the manifest, absent
  from the precache list).
- **Navigation handling with `ignoreSearch: true`** — this is what makes the
  manifest shortcuts (`./index.html?tab=add`) work offline; exact-URL matching
  missed on the query string.
- **`skipWaiting()` removed from install.** A new worker parks in `waiting`; the
  update banner posts `SKIP_WAITING` and the page reloads on `controllerchange`.
  Previously the new worker took over while the old `app.js` was still running.
- Navigation preload enabled; `SW_VERSION` bumped to 2.8.0 alongside
  `APP_VERSION`.

---

## Smaller fixes

- **Pinch-zoom restored.** `user-scalable=no` / `maximum-scale=1` removed from
  the viewport meta, and the `touchmove` / `gesture*` blockers removed from
  `app.js` (WCAG 1.4.4). The double-tap-zoom suppression is kept, since that one
  fires by accident on the steppers.
- **Numeric inputs bounded at both ends** via `clampField()` — previously only a
  floor. `1e12` in a weight box no longer propagates into app state.
- **`maxlength` on every text input**, plus `cleanStr()` caps in JS (names 80,
  notes 300).
- **IDs now use `crypto.randomUUID()`.** The old slug scheme stripped every
  non-`[a-z0-9]` character, so all Hebrew movement names collapsed to
  `custom--<timestamp>`.
- **`userName` moved from localStorage to IndexedDB** (with one-time migration).
  It's the only PII in the app and "clear all data" never touched it — it does
  now, and the welcome modal reappears. Same for the last-export marker.
- **Storage failures surfaced.** `noteStorageError()` distinguishes
  `QuotaExceededError` and shows it in red in the footer instead of silently
  swallowing it.
- `CSS.escape` via `cssSel()` on the two `querySelector` calls that interpolate
  a field name — these threw on any name containing a quote.
- `openDB()` now memoises its promise instead of reopening the DB per call.
- `URL.revokeObjectURL` deferred 30s so the download reliably starts.
- `mobile-web-app-capable` added next to the deprecated Apple variant.

---

## Left for you

1. **Self-host the fonts** and tighten the CSP to `font-src 'self'` /
   `style-src 'self' 'unsafe-inline'`.
2. **Server response headers**: HSTS, `X-Content-Type-Options: nosniff`,
   `Referrer-Policy: no-referrer`, `Permissions-Policy` denying
   camera/microphone/geolocation/usb, and `frame-ancestors 'none'` as a real
   header.
3. **Automate the version bump** — `APP_VERSION` in `app.js` and `SW_VERSION` in
   `sw.js` are still synced by hand. A missed bump means users stay on stale
   code, which is now a security concern and not just a UX one.
4. Exports are still plaintext JSON containing the name, bodyweight history, and
   full training log. Normal for a backup, but worth a line of UI text next to
   the export button.
# Community foundation and cloud sync — v3.0.0 — 2026-08-26

- Added a Supabase/PostgreSQL community backend migration with deny-by-default
  Row Level Security for private records, profiles, follows, blocks, workout
  posts, cheers, reports, and account-deletion requests.
- Added magic-link authentication, profiles, athlete discovery, following,
  a follower/public feed, explicit workout sharing, comparable-result views,
  reactions, reporting, blocking, and a 30-day deletion workflow.
- Existing and new workout records remain in IndexedDB for offline use. Cloud
  migration requires explicit consent, and an IndexedDB outbox retries writes
  after connectivity returns. Remote private records hydrate a new device.
- Social posts are sanitized snapshots: bodyweight, measurements, session and
  WOD notes, partner tags, email, and backups never enter the public post.
- Reconciled the unfinished working-tree regression pass: fixed edit identity
  corruption, stale ladder state, EMOM switching/input behavior, custom-WOD
  deletion, backup tests, text scaling, and tiered achievement artwork.
- Added setup, privacy, terms, and CI documentation. The Community tab remains
  in safe setup mode until `cloud-config.js` contains a project URL and public
  publishable key.

## 2026-09-09 — immersive reference reimplementation, audit and pass 1

Authority: external haimunia-claude-handoff/CLAUDE.md, IMPLEMENTATION_SPEC.md,
SCREEN_ACCEPTANCE.md, PHOTO_MAP.md, ALL_PHOTOS_MANIFEST.md, VISUAL_QA_PROTOCOL.md,
and design-reference.jpg. No applicable AGENTS.md exists in workspace/handoff/parents.
Existing dirty app.js, cloud.js, index.html and CHANGES.md are retained.
Route inventory: renderLogTab/add; renderCalendarTab/calendar (History);
renderHistoryTab/history (Progress); renderWodTab/wod; cloud.js/community.
Achievements, notifications, settings and welcome are existing modal render paths.
Preserve all delegated actions and IDs, cloud/storage logic, theme initialization and CSP.
Photo aliases already exist locally; source originals remain in external handoff.

Baseline actual Chromium screenshots: /tmp/immersive-qa/before/{add,calendar,history}-{light,dark}-{390,430}.png.
Baseline measurements: Add/History/Progress sheet 42.10% at 390 and 42.28% at 430;
36px titles; 68px nav; no document overflow. Media ends at 371/410px while pages
extend 954–1841px, violating full-page media. Five nav destinations instead of four.
Negative sheet margin reduces effective inner padding to 2/4px; target 17.94/19.78px.
Add subtitle is occluded by sheet. Calendar nests a blue bordered panel inside sheet.
Progress sheet must move to 38%; target 36–40%. These are failing baseline results.


## Final QA ledger — 2026-09-09

Three correction passes were completed for Add, History/Calendar and Progress at 390x844 and 430x932. Screenshots and measured geometry are in `docs/visual-qa/immersive/final/`; isolated HEAD baseline capture is in `before-head/` (the existing dirty-tree baseline is in `before/`). Final scene measurements: Add sheet 42.0% (390), 42.3% (430); History/Calendar 40.0% / 40.2%; Progress 38.0% / 38.2%; title 34px; 17.94–24px sheet padding; mobile bottom nav 68px; photo media touches all scene edges and continues under the sheet; no horizontal overflow.

Final verification: `scripts/visual-qa/verify.mjs` — 72 cases, 0 axe issue groups, 0 overflow cases; `scripts/visual-qa/community.mjs` — 8 populated Community/Notifications cases, 0 axe issues; isolated `community-render-cost.mjs` — 5.5ms at 4x; `npm test` — 1512/1512; `npm run check-version` and `npm run check-vendor-version` pass; `test/calendar-view-mode.test.mjs` and `scripts/browser-check/duration.mjs` pass. Full sequential run logs are in `docs/visual-qa/immersive/logs/`.

Deliberate differences: the production app keeps its existing fixed IDs and delegated save bar, so Add’s `שמירת אימון` label is written into the existing `#saveBtnLabel`; desktop retains the existing sidebar/context semantics; Settings and dense dialogs remain solid reading surfaces while their scene edge treatment uses local club photography.

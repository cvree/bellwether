# Bellwether

A private symptom journal that lives on your device. The early sign, written down.

You build a check-in around your own situation — skin, gut, migraine, POTS, fatigue, a diet
experiment, whatever you're actually tracking — answer it in about a minute a day, and watch
the trends come out over weeks. When you have an appointment, you print a summary and take it
with you.

**And you don't start from nothing.** Almost everybody who tracks anything seriously was already
tracking it somewhere — a notes file, a chat with themselves, a photo of a page, or just an
account of how the last fortnight went. Paste it in, or hand over a screenshot, and
[**Import your notes**](#import-your-own-notes) reads it into meals, doses, numbers, bowel
entries and notes *on the dates and times your own notes give*. Months of shorthand — or three
sentences of prose — become a journal in about a minute, and you approve every single row before
one word of it is written.

**And once it is a year deep, you can open a drawer of it.** [**Search**](#search) is one box
over every note, meal, dose, bowel entry, ritual, flare, lab result and hour outside — plus the
questions your survey asks and the screens themselves. It answers on the first keystroke, every
result opens the thing it found on the day it happened, and `itch>=8 -dairy` is a question you
can actually ask.

There is no account, no backend holding your journal, and no tracking. Out of the box, after
the app has loaded once it makes **no network requests at all** — it installs to a phone's Home
Screen and works completely offline.

Four things can change that. All are opt-in, all are off until you turn them on, all leave
everything else working exactly as it does now, and **all four name what they are sending before
they send it**:

- **Import your own notes.** The one path here whose payload is your own writing, because the
  writing is what is being read. It asks every time, lists the entire payload first, and nothing
  reaches your journal until you have seen every proposed row beside the words it came from.
  [What it sends, and what it refuses to do.](#import-your-own-notes)
- **AI observations.** Add your own Google Gemini API key in Settings and it sends a minimal
  summary of your logged numbers *when you ask it to*, showing you exactly what first.
- **Sync across devices.** Turn it on and your journal follows you from phone to laptop —
  encrypted on your device before it's uploaded, with a passphrase that never leaves it. Local
  saves still never wait for the network. [How it works, and what it doesn't
  claim.](#optional-sync-across-devices)
- **Daily context.** Turn it on and each day gets the weather attached — temperature, pressure,
  UV, air quality, pollen. The request carries a latitude and longitude rounded to about a
  kilometre and *nothing else*: no identifier, no name, nothing from your journal. What is stored
  is a reading of the sky, not a record of where you were.

You will not find "everything stays on your device, always" written anywhere in this app, because
with any of those four switched on it would not be true. What it says instead is which switch is
on and what that switch sends — on the privacy card in Settings, which rewrites itself as you
change them.

> **Not medical advice.** This is a personal tracking tool. It does not diagnose, treat, cure, or
> prevent any condition. It surfaces *possible patterns* in your own logs and never claims a cause.
> For medical concerns, symptoms, medication changes, restrictive diets, fainting, allergic
> reactions, abnormal labs, or major health changes, consult a qualified healthcare professional.

---

## What it does

**How often it asks is yours.** Every screen in this app used to assume one thing without ever
saying it: that the check-in is daily. For plenty of people it is. For plenty of others it is
exactly why their journal has eleven days in it — they were asked every morning for something that
moves over months, complied for a fortnight, missed a day, watched a streak reset to zero, and
stopped. Settings now asks the question plainly, with nine answers: every day, weekdays, every
other day, three or two times a week, once a week, every two weeks, once a month, or only when you
open it.

And the app *means the answer*. The unit is the **period**, not the day: "once a week" means the
week owes one check-in, so doing it on Saturday is worth exactly as much as doing it on Monday.
The streak counts weeks. The ring on Today counts what today asked for. The reminder does not fire
on an evening when nothing is owed. And on the six days a week a weekly journal has nothing to
ask, the card at the top of Today says so — *this week is in, next from the 31st* — because
otherwise choosing a slower cadence buys nothing but the same guilt on a longer timer.

**And each question can ask less often than the journal does.** The pain score is a daily
question; the weight is a weekly one; the tape measure round your waist is monthly, and being
asked for it every morning is how a thirty-question setup becomes one nobody fills in. Any
question can be set to weekly, fortnightly or monthly in Edit Setup. It then disappears from the
check-in for the rest of its period and comes back when the next one opens — it is never disabled,
never leaves your charts or exports, and Detailed Log still has it if you want to answer it early.

**Time off is a thing you can say.** Every long-running journal dies in the fortnight somebody
spent in hospital or on a beach, because coming back to a broken streak and a wall of gaps feels
like starting over. Pause it — for a week, a fortnight, a month, or until you say — and nothing is
due, nothing is missed, and the streak steps over it rather than resetting. An appointment pack
from a weekly journal says "22 of 24 weeks kept" rather than "31 of 168 days", because the gaps
between are the schedule and a document a clinician reads has to be able to say so.

**Reminders, plural.** A check-in belongs at the end of the day; meals belong at meal times,
because the point of tracking food is logging it while you eat. Add as many named times as suit
your day, and the ones whose job is already done stay quiet. On the phone app your phone schedules
them itself — they arrive with the app closed, and no server, account or identifier is involved in
making that happen. In a browser they come out as one calendar file that does the same job.

**The first two minutes.** First run is a doorway and six acts, not a wizard, and there is one path
through it. A full-screen hero — *Your health, remembered.* — over a journal that is already alive: a
rating, a photograph fourteen days apart, a note about a bad night, a dose ticked off, a flare that
ended, three months of trend with the flare shaded behind it, with the five checkable promises
about the build one tap below it. Then a doorway, and six numbered acts.

**Who is this journal for?** A name and an age, both refusable, neither numbered — a doorway, not
step one of a registration. It is here because everything after it is warmer for having been
asked: the app opens with *Good morning, Sam* rather than *Good morning*, and the two facts a
clinician asks for first are already at the top of anything you print. The screen argues by
consequence rather than by nagging: the greeting is quoted back with your own name in it as you
type, and the header of an appointment pack fills in beside it. Skipping is a button, not a
greyed-out apology, and the age is stored as the year you were born so it is still right in three
years. Both are editable in Edit Setup afterwards.

**What are you tracking?** The only question that cannot be defaulted — and once it is answered,
the screen draws the ones that follow it: your questions, your photographs, everything else a day
holds, your first entry. It also says what those screens will and will not do: that nothing is
switched on yet, that nothing gets photographed unless you ask, and that all of it exists again in
Settings with more on the table than first run ever shows you.

**And then the question the setup never used to ask: what do you want to find out?** Everything up
to here establishes *what* you track, which is the part an app can guess at. Nobody ever asked
*why* — and the why is the only fact on the screen worth tailoring around. Two people both pick
Eczema: one wants to know what sets it off, one wants to know whether the cream she started in
January is doing anything, one wants twelve weeks of evidence to put in front of a dermatologist
who gets ten minutes. Those are three different journals, and they used to get the same one.

So: five cards, and the last of them is *nothing in particular — just keep the record*, which is a
real answer and is never sulked at. Picking one opens underneath itself and answers with
**machinery rather than encouragement**: the comparison the app will actually run on your own days,
the buttons and photo subjects that will arrive suggested two screens from now, named so you meet
the consequence of your own answer immediately — and **the date the first answer can exist**, which
is twelve days on the record at the pace it is currently set to ask. Nothing here says "great
choice", and nothing here switches anything on: an aim moves the app's opinion, never your hand.
Every question, photograph and button is still a card you say yes to, one at a time. What it does
change is what gets offered first, and which rows on the question cards are marked *your aim* —
because somebody who told the app their question two screens ago and is then left to scroll past
the answer to it has been failed by the app rather than by themselves.

**Three acts, and each of them walks you through it.** The questions, the photographs and
everything else a day holds are the three screens with more on the table than anybody weighs in a
glance, and all three are now dealt out **one card at a time**. There is no list beside them and no
preset to arrive on — both were the same mistake in two shapes, a journal assembled by a default
rather than by the person who has to answer it at 7am on the morning they feel worst.

**And any of them can be answered in one tap once you know it isn't for you.** The argument for a
card at a time holds on the first card and stops holding on the fourth: somebody who has said *not
this one* three times running is no longer deciding, they are dismissing, one screen at a time. So
under the Yes and the No there is a third answer — **None of the 7** — which says no to every card
that is left and names how many that is. It is an answer, not an escape hatch: every remaining
subject is recorded as a no, every yes already given survives, Back returns you to the card you
pressed it on, and a yes that owes a screen (the body map, the photo angles) still gets it. Taking
it on both decks is the difference between eighteen screens and five.

**What should it ask you?** One group of questions per screen: how big the group is and what
answering it feels like (*five questions here — three rated 1–10, two yes / no*), **the control
drawn beside every row** — ten rungs, a Yes beside a No, a keypad, three lines of text, because
almost nobody has been asked to design a survey and nobody needs a yes/no explained once the Yes
and the No are sitting there — *ask me all of them* and *none of these* as single taps, and the
running cost of the whole check-in under your thumb, which answers back every time it changes.

**Nothing arrives switched on but your daily number.** There is no Quick, no Balanced and no
Thorough. Three unlabelled sizes is a slider with no units, and whichever one the app lands on is
the app deciding what you track — the person most likely to tap "Thorough" is the person least
likely to still be answering it in March. The packs still have an opinion and still say it, on the
row it is about: *most people keep this*. Then they wait. The last card of the pass is the one
thing a pack cannot supply — *anything it should ask that isn't here?* — which takes a question in
your own words as a 1–10, a yes/no, a number or a few words, drawn as you write it.

**And it does not ask you to agree with yourself at the end.** A review card after a pass that
asked about every single item is the app asking you to confirm a list you built row by row. It
reads as doubt, and the second reading of a list you have just made is the reading where you stop
caring. The last answer is the answer; the next act starts.

**What's worth a photo?** Not a switch — a question about subjects, one to a screen. Specific body
areas off a tappable map, flare-ups as they happen, progress shots, meals, products and labels,
swelling, wounds and healing, or anything worth a picture. Each card holds one up: what it is, the
same frame twice six weeks apart, what it turns out to be worth later — *the flare you photograph
on the bad night is the one you can still show somebody in March* — whether people tracking what
you track tend to keep it, and a **Yes beside a No**. Both answers move on and a no is remembered
as a no. The contact sheet of labelled empty frames fills in underneath as you answer, and every
subject becomes a real photo question with its own baseline, so every shot lines up against the
last one *of the same thing*.

**Nothing here is ticked for you, and nothing is left dangling.** Every subject on this screen ends
with a camera pointed at your own skin, plate or bathroom shelf, so the app suggests and then
waits. The two subjects that need one more fact — *which body areas*, *which angles* — now ask for
it **inside the pass**, on the card straight after the yes, rather than on a screen the pass hands
back to. Saying yes to the body map and then never being shown a body map was the one way a guided
pass could strand the exact person it was there to help.

**What else should it keep?** Meds and creams, meals, flares, the bathroom, weight — one to a
screen, a yes beside a no, and each yes drawing itself into the row of one-tap buttons underneath,
so the dashboard is assembled in front of you out of your own answers rather than filed away to be
discovered later. Say yes to the meal log and the app makes its one offer of the whole flow: a
short, guided way to connect a free AI so that a photograph of the plate becomes the entry. Three
taps, no typing — the key is lifted off your clipboard the moment you come back from Google's page
— and *not now* is a complete answer that leaves the journal exactly as it would have been. Then the two questions that are not about *what* a day holds but about *when* it
is asked for: how often it should ask at all, and a nudge if you want one, at a time you choose —
in that order, because the reminder is about when in the day and the cadence is about whether the
day is even one of the days.

**And then you are shown around.** The journal is born onto a home screen full of controls you
chose a minute ago and have never seen working, so there is one pass over it — once, on this
device, and never again. It dims the app and cuts a hole around **one real control at a time**:
the card that asks today's questions, the row of buttons you assembled, today's check-in ring, the
+ button, the + button *held*, History, and the gear. Nothing here is a mock-up, because the thing
being taught is where your thumb goes and a picture of a button teaches nobody where a button is.
It spends a whole stop on the two things nothing else explains — **holding the + fans every screen
in the app out from under your thumb**, and what is actually behind the gear, listed rather than
left to be discovered in six weeks — and there is a way out on every card. It only ever runs itself
once, which is exactly why **Settings → A look around** can ask for it again: somebody who skipped
it on day one, or who has just handed the phone to the person the journal is actually for, should
not have to erase their data to be shown around.

Then your first real entry — ten large targets you can tap or slide a thumb across, with the card
taking the colour of the day as soon as there is a number — and the part that is the point: **the
card you just filled in flies into place as the first card on a timeline**, the rail draws downward
past it into the days you have not lived yet, and the streak counts to one. A journal is a promise
about the future, and watching your own first entry become the first thing on a timeline makes that
promise in about three seconds.

**And then it puts three dates on that promise.** *Keep going and it answers what memory cannot* is
a lovely sentence and it is not an answer to the only question anybody has at the end of a setup,
which is *when does this start being worth it?* So the last screen ends on three dated rungs —
your first week, twelve days on the record, thirty days across a few different weeks — each one
carrying what becomes possible there, worded around the question you said you came with. The dates
are arithmetic you could check: the rungs are the same ones every finding in this app is graded on
(`src/lib/evidence.ts`), the pace is the cadence you chose two screens earlier, and choosing *once
a week* moves every date rather than being quietly ignored. It also says out loud that missing days
moves them, and that nothing is lost when they do. The same arithmetic comes back on **Insights in
week one** — the screen where a new journal has nothing to show — so *nothing stands out yet* is
followed by how many more check-ins, and when, rather than by a shrug.

**Nobody has to start from nothing.** Almost everyone arrives at a health journal having already
tracked it somewhere — a notes file, a chat with themselves, a photograph of a page — and a journal
that opens with one day when it could have opened with ninety is the single largest thing this flow
can still do for somebody. So the last card offers it: four lines of real shorthand beside the
meals, doses, numbers and movements they become, *on the dates the notes themselves give*. It is
honest about the price in the same breath — this is the one feature in the app that sends your own
writing anywhere, it needs the optional AI connection, and you approve every proposed row beside
the words it came from before one of them is written. Say yes and the app opens on that screen
instead of an empty dashboard, with the tour waiting at the dashboard rather than skipped. *Not
now* opens the journal exactly as it would have been, and the offer stays on Today for the first
fortnight.

Nothing is ever demanded and nothing is ever assumed — two different promises, and the flow makes
both. The way forward is live on every card and *not this one* is a real button rather than a
greyed-out apology; and no question and no photograph is switched on by anything but a tap. There
is no "set everything up in detail instead" door beside it, and no list beside the passes either: a
second way through is an admission that the first one does not do the job, and an optional guided
pass is one the people who need it never take. The main number you pick is what Today asks for every day, what the
streak counts, and the first figure in an appointment pack; everything here is changeable whenever
you like, from Edit Setup and from the Quick Add editor.

**Build your own survey.** Start from a question pack — Eczema/Skin, Carnivore/Diet, POTS,
IBS, Migraine, Allergy/MCAS, Fatigue/Long COVID, Autoimmune, Thyroid, Joint Pain, General
Wellness, Wearable — mix several, switch individual questions off, add your own, and reorder
them. Each question has independent visibility across five surfaces: quick log, detailed log,
dashboard, charts, export. The editor groups them into collapsible sections per pack, with a
filter across the top — sixty questions in one flat list was unusable.

**Log in about a minute.** Quick Log batches four questions per screen with big tap targets and
auto-advance. Your recent answer for each question — a 7-day median for scales, yesterday for
toggles, the last value for numbers — is marked with a dashed ring on the value itself, so
accepting it is one tap and ignoring it costs nothing. It is never a banner asking whether today
was the same as usual, and it is never filled in for you.

**The long form is a form, not a scroll.** Detailed Log lays its sections out as cards — each
with its own sticky heading, answered count, and fold — one column on a phone, two from 900px,
three from 1320px. It is the only screen in the app that widens on a desktop, because it is the
only one that is a form rather than a list. Any past day stays editable from the calendar.

**Numbers are typed, not clicked eleven times.** Tapping a weight opens a keypad — the value at
reading size, a nudge row, ten keys. It takes one decimal for a weight and none for a step count,
and digits, Backspace, Enter and the arrow keys all drive it from a physical keyboard.

**The Diary — one page for the whole day.** Meals and the routine share a screen, over one date,
because "what did I have" and "did I take the morning lot" are asked in the same breath. A sticky
day pager moves both, so filling in yesterday evening — the food *and* the doses — never means
changing tabs. At the top, the day's two headline numbers: what you ate, and how much of the
routine you have answered. Everything is on the page at once; nothing is behind a tab, a toggle
or a sideways scroller.

**Food.** A calorie ring, macro bars, and the day grouped
into Breakfast / Lunch / Dinner / Snack / Drink with per-meal subtotals. Log a meal with the
category, time, description, serving, weight or quantity, notes, and a photo. Calories and macros
can be typed, or estimated by AI if you've set that up — from a photo, from your description, or
from both. Every estimated value is labelled **AI Estimated**, is editable, and is never stored in
the same field as a number you entered. Estimates read "about 520 kcal", because that is what
they are.

**And it gets faster the more you use it.** MyFitnessPal is quick because you never type a food
twice — that's two million foods on a server, which an app with no server and no account cannot
have. So this does the half that actually does the work: people eat the same thirty or forty
things on repeat, so **your library builds itself out of your own logs**. Search it, or pick from
Recent / Frequent / Favourites, and re-logging is one tap — with a serving stepper for anything
that isn't exactly one portion, quick-add calories for when you can't be bothered, and
copy-yesterday for the days that repeat. Set daily targets if you want them; leave them blank and
the diary just shows what you ate. Fixing a food's figures once fixes them everywhere after.

**Your routine — meds, supplements, creams, products.** The things you take and use every day,
as a checklist that answers in one tap. Add an item with a name, a kind (medication, supplement,
cream, product, food or drink), a dose in your own words — *500 mg*, *2 pumps*, *pea-sized*, *1
scoop* — and the parts of the day it belongs to. It then sits on the Diary and on the dashboard,
grouped into Morning / Midday / Evening / Bedtime, and **ticking it off is one tap, with no form
in the way**. The same tap unticks it. Anything you only take when you need it lives in a separate
**As needed** row, offered but never counted as missed.

Two things keep a long routine short. A slot with more than one thing left to take offers
**All 4** — one tap for the handful you swallow in one go, one Undo behind all of it. And a slot
you have finished **folds into a single line**, so a nine-item routine is four rows by bedtime
and the day still fits on one screen. Opening it again is one tap; nothing is ever hidden that
you cannot get back.

Adjusting is one more tap: today's dose can differ from the usual one without editing the plan,
and a dose you deliberately decided against is recorded as a **skip** — which is a different fact
from a box you simply never ticked, and the app never conflates them. Every entry keeps its own
copy of the name, kind and dose as they were the day you logged it, so renaming an item, changing
its dose, or deleting it outright never rewrites what a past day says happened. Doses taken and
"routine completed" can be charted next to your symptoms, and both the per-dose log and the plan
behind it come out in the export.

It is a written record and nothing more. It does not know what interacts with what, does not
check doses, and will not tell you whether something is working.

**Rituals — the routine as a process, and a weekly tune-up that keeps it honest.** A shower is
not one tick. It is the wash, and then the ninety seconds afterwards where the moisturiser either
goes on damp skin or doesn't work — and that second part is the one that matters and the one that
gets dropped. So a **ritual** is an ordered list of steps with one name on it: *Shower & after*,
*Morning meds*, *Night meds & supplements*, *Wind-down*. Six are already written out, steps and
hints and all, and the two medication ones **fill themselves in from the routine you already
keep** — pick "Morning meds" and everything filed under Morning is already a step, carrying its
dose.

On Today each one is a single row. **Tapping the row finishes the whole ritual**, in one write,
with an Undo in the toast; tapping it again takes it back. Beside the name: the step count, the
part of the day, a streak once there is one, and seven dots for the week behind it. A day the
ritual was never asked for is drawn as a gap, not as a failure.

The row's second control opens the **player** — the same ritual as a list of very large steps,
one of them lit as the next, each carrying its reason in a few words and, where the instruction
has a number in it, a timer you can start and ignore. A step can point at something in your
routine, and ticking it writes the dose into your medication history exactly as the routine
checklist would.

**Once a week, the app asks how one ritual is going — one at a time, and never two on the same
day.** Each ritual is given its own weekday, spread as far from the others as the week allows, so
four rituals set up on the same Sunday do not all come back on the same Sunday. Two tune-ups can
never land within two days of each other whatever their days say, none appears before there is a
week and three days of history behind it, and "not now" costs two days rather than switching the
thing off.

It opens with the week you had rather than a question — the seven dots landing one at a time, the
count, the best run so far, and a line that does not pretend a hard week was a good one. Then two
one-tap questions, the second of which is skipped entirely on a week nothing got in the way of.
Then it pays out: a short list of **changes to your plan written from your own week** — *make
"Moisturise within 3 minutes" optional, 2 of 7 days* · *move it to bedtime, you usually finish
around 9:55 pm* · *stop asking on Wednesday, not once in four weeks* — any of which is applied by
tapping it. "It's good — leave it" is a real answer, and it is listed first on a week that went
well.

A run is a record on the same terms a dose is: it keeps its own copy of the name and of how many
steps were required the day it happened, so trimming a step tomorrow can never un-complete a
fortnight. An absent run means nothing was said; "not today" is its own, separate fact. Rituals
come out in the export as two sheets — the plan, and one row per ritual per day whose `step_list`
column names the steps actually done, which is the column worth sorting by.

**Bowel movements.** A quick log with Bristol type, amount, colour, consistency, urgency,
straining, discomfort, notes, and an optional photo. If you ask it to, AI can suggest the
observable attributes from a photo — Bristol type, colour, consistency, form, and nothing else.
It will not tell you what anything means, and the photo stays on your device unless you
explicitly choose that analysis.

**One tap is a whole day.** Today opens with the **Daily Pulse**: your main number, ten large
targets, and the tap *is* the save — no button, no confirmation, no screen. The line under it is
read back out of the journal rather than asserted, so it says "Nothing recorded yet" until the
number is actually there, and it says which end of the scale the number is at. For most people on
most days this is the entire interaction, and a year of one honest number beats a fortnight of
forty.

**And then the next question takes its place.** One slot, and whichever question the day is on is
in it. Answer the number and the answer is said back where you gave it — *8/10 saved for today — a
hard day* — it holds for a beat, and then the whole thing lifts away and the next question arrives
in the same place, at the same size, with the same weight. Nothing moves down the screen and
nothing appears underneath: a whole daily review can be done from the top of the first card at the
speed of tapping, with a progress line saying how much is left (*4 of 12 answered*) so it is never
an open-ended demand.

This used to be a second card under the pulse, and two questions were on the screen at once — the
one just answered still holding the top of the card with its confirmation, and the one being asked
in a smaller box below it. A card that has to tell you where to look has already lost the tap. The
beat before the swap is the confirmation rather than a delay, because moving on the instant a
finger lands would make anybody doubt the tap registered, and that is the one thing a journal may
never do.

What it asks first is decided by what your packs are about, what kind of day you have said it is,
and **what you actually record** — somebody who fills in their weight every morning and has never
touched "possible triggers" is asked for the weight, whatever the template thinks. A question
finished by one tap hands over by itself; a number or a multi-select waits for **Next**, because
snatching a field away mid-keystroke is the app racing you. **Back to the question before** walks
out the way you came, all the way to the number — which is how *tap it again to clear* is still
true five questions later — and the slot always opens on the number when you come back to the app,
even on a day you rated at breakfast. **Skip this one** and **Done for now** are both there, and
neither is remembered: tomorrow it asks again, because a journal that permanently stops asking on
the strength of one impatient tap has started deciding what you track.

**Detail comes after, never in front.** Under it: the things a question cannot be — the
routine still owed, the camera, and the note, which is last because it is the one that needs
typing. Nothing already answered is offered, and a photo is only asked for on a bad day or after
a week without one.

**Today's check-in, and how much of it is in.** The way into the rest of the day used to be a
dashed link at the foot of the card that said *Add more detail* — a name for an afterthought,
attached to the thing this app is for. It is **Today's check-in** now, and it carries the state
of the day rather than an invitation to do more work: a ring that fills as far as today has got,
one small mark for every single thing today asked for, and a line that says where you are (*25 to
go*). The count at the top of the pulse card and the bar under it read the same arithmetic, so
there is exactly one size for today anywhere on the screen — and the estimate under an untouched
one is arithmetic too, four seconds a thing, so a thirty-three-item morning is offered as two
minutes rather than as one. Every mark is drawn from the journal, so the number moves the instant you
answer anything, anywhere — a tap on the pulse, a question in the queue, a dose ticked off the
routine — and it moves back down if you clear one.

What the fraction counts is **what your own setup asked for**: your questions, and the doses
scheduled for today. A skip counts as answered, because the question a routine row asks is "did
you deal with this". A photo, a note and a meal are shown beside the ring and never inside it —
the right number of notes for a Tuesday is not one, it is however many were worth writing, and a
progress ring in a medical journal is not allowed to invent a target nobody set.

**And then the day closes.** Answering the last thing today asked for is the moment this whole
app is arranged to produce, and it is drawn as one: the card settles, a wash of your pack's own
colour crosses it, the tick stamps into the middle of the ring, and the row of marks under the
title is replaced by **the fortnight behind today**, arriving day by day with today's mark solid
on the end of it. It fires once, on the answer that closes the day — arriving later on a day you
already finished is silent, because a receipt played every time you open the app is a noise you
learn to ignore. The line reads *Today is fully on the record* — a statement about the record,
not about you.

There is still no badge, no score and no streak counted at you, and that row of days is not a
scoreboard: a day the journal has nothing on is a hairline and nothing else. No red, no gap
count, no "four missed". The satisfaction is the one closing a page in a paper journal gives —
nobody said well done, the thing you are making is simply thicker than it was.

**And today is at the top of History**, with the same ring and the same numbers, broken down part
by part: *Questions 6/27*, *Routine 0/4*, *Photo —*, *Note —*, *Meals —*. The record used to
begin at yesterday, which meant the one day you are actually living was the one day it could say
nothing about. Both screens read the same module, so they can never disagree about your own day,
and the card is the way in: tapping it opens the check-in you were being told about.

**One hand.** The whole app is reachable by the thumb of the hand holding the phone. The bar is
**Today**, **History** and a **+**, and those three never swap places — the value of a bar to a
thumb is that the thumb stops needing to look. The + sits at the end of it, on the side you hold
the phone, because that corner is where a thumb rests.

Hold the **+** and slide: every destination in the app — the daily log, Insights, the diary, sun,
labs, experiments, your routine, photos, export, settings — fans out from that corner along the
arc a thumb actually sweeps, the one under your thumb lights up as you cross it, and letting go
opens it. It asks for a *direction* rather than a position, which is the one shape of control
that survives being used without looking at it.

Back means where you came from, not "Today" — it says so in words, and it is on the bar, in the
header, on either side edge as a swipe that peels the screen off under your thumb, and on the
phone's own back button. And when something is at the top of a long screen, pull down on the +
and the page slides into reach; the bar stays where it is. Left-handed puts all of it on the
other side. The + is still one tap from anywhere and still opens everything a day can hold —
check-in, food, routine, photo, note, bowel movement, measurement — landing on Today, which is
the day it adds to. History is the month, the last fortnight in words, and the two doors out of
it: Insights and the Diary. Settings lives in the header and in the fan, because a preference is
not a destination.

**Open it, log it, close it.** **Quick Add** sits under the pulse, and it is shaped like your
condition: a POTS journal opens with water, a heart rate and a flare; a skin journal with a camera,
a routine and a trigger; a gut journal with the bathroom and the day's meals. Fourteen buttons
exist — check-in, food, drink, bowel, routine, photo, flare, symptom, heart rate, water, trigger,
note, measurement, diary — and one only ever appears when your own setup has a question behind it,
so there is no button that opens an apology. Water is one tap and one cup with an Undo in the
toast; Flare marks one on the day it happened and then reads *2 logged today*; Symptom rates
one question 1–10 without the whole check-in; Heart rate takes lying and standing and prints the
jump between them. **The + button in the navigation bar shows exactly what you put on your
dashboard** — one list, two doors — with everything else one tap further down and the editor a tap
after that. **The buttons stay where you put them**, on both, because the value of a button on a
phone is that after a week your thumb knows where it is. Moving one is a gesture rather than a
settings trip: hold a button until it lifts, drag it, and the rest slide out of the way — or hold
Alt and press an arrow key, or use the arrows in the editor. If you would rather the row sorted
itself by what you tap most, that is one switch in the editor. **Again** is the list under it, and it is the shortest path in the
app — your most-logged foods, the spot you photograph, the number you record, the note, one tap
each, ranked together so it is your own week in your own order. **It deliberately never offers a
dose**: the Routine checklist a couple of inches below is already showing every one of those with
a better control on it, and a row that ranks by frequency would otherwise open with the same three
medications every single day and push everything with no other home on Today off the bottom of
itself. What is left is short, so all of it is shown — five rows at most, each with the kind drawn
as a tinted medallion, the name and the detail on one line, and a **+**. Nothing behind an edge,
nothing truncated, no arrows to reach the rest. **Today's Logs**
is one timeline carrying check-ins, meals, bowel movements, doses and photos in the order they
happened.

Logging is optimistic and reversible. Sheets close on the tap, the row is on the timeline
before the next frame, and the receipt arrives as a toast with an **Undo** in it — which beats a
confirmation step, because it charges only the people who actually made a mistake. Deleting a
log keeps its photo until the Undo has expired, so an Undo never brings a meal back without it.

**See what's happening.** **Insights** is the second tab, and it runs down the questions in the
order people ask them: *over what period* (a range selector at the very top — 30 days, 3 months,
12 months, all — which everything below it genuinely re-reads), *how am I right now* (the hero),
*how does that compare* (four figures and no charts among them), *what has it been doing* (one
trend chart), *how bad were the bad bits* (flares), *what does a year look like* (the heatmap),
*what kind of days are they* (the spread), and *is anything related* (the explorer). Week by
week, the years overlaid, seasonal averages and the scatter each sit behind a labelled expansion
control. Pin up to four metrics and they're still there tomorrow — the first one is what the
whole screen is about, and every one of them is drawn in the trend chart. Food and bowel logs join as derived daily metrics (calories, macros, movement count,
average Bristol type, urgency, straining, discomfort).

**The spread of days.** An average of 5.2 is the same number for someone who scores 5 every day
and someone who alternates 2 and 8, and those are not the same life. Ten columns, one per score,
each carrying its own count, in the year block's colour ramp — then the typical day, the most
common day, the spread in one word (*steady*, *mixed*, *swinging*), and how many days were hard.
"How many days were actually bad" is a count, not a curve.

**Flares, marked by you, on the day they happen.** A chronic condition is not a smooth line with a
slope; it is long stretches of "fine, mostly" broken by days and weeks that reorganise your life.
One tap marks one, on today, complete — **there is no stopwatch to remember to stop**, because the
day you would have to stop it is a day you feel fine and are not thinking about it. Twice in an
afternoon is two flares, which is the honest answer and the one a start/end model could not
represent at all. Everything past that first tap — a name, a note, or *this one ran on* if it
turned out to be the start of a bad fortnight — is offered afterwards and never chased.

**Nothing is detected automatically**, which is a decision rather than a gap: a run of 7s is not
always a flare, and an app that invents medical events in your history and then reports statistics
about them has done something worse than nothing. The app does the arithmetic: how many this month,
how often they come, coverage, average, median, peak and its date, hard days, the fortnight before,
the fortnight after, and the clear days since the last one — then a year of them against the year
before, with a flare crossing New Year counted in both and a day carrying two flares counted once.
Each flare has its own screen, and its chart draws a fortnight either side, because a bad day drawn
on its own always looks like a bad day, and drawn with the fortnight before it, it looks like what
happened.

**The long view**, folded under the year block: a point per calendar month across the whole
journal, this month against the same month last year, best and hardest month, the longest
unbroken calm run, the years overlaid, and seasonal averages. This is the section with the most
ways to mislead, so it has the most floors — a thin month is not plotted, a comparison needs both
sides solid, seasons stay hidden until most months have two years behind them, and a calm run
counts only days logged back to back. Where something is hidden, the reason is printed.

**The trend chart is the comparison.** Metrics that genuinely share a scale — the 1–10 ratings
— share one chart with a fixed 1–10 axis. Anything with its own unit gets its own chart
underneath: same width, same dates, its own axis, one crosshair moving across all of them at
once. The metric the screen is about leads — heaviest line, tallest chart, its 7-day average
dashed in behind it — and the flares you marked are shaded behind every chart in the stack. The
old chart put severity and step count on one pair of axes and printed a note asking the reader
to "compare shapes, not heights"; worse, weight in kg and severity 1–10 land in the same numeric
range, so that chart looked perfectly reasonable and was meaningless. The version before this
one had the opposite fault: a picker that let you pin four metrics above a chart that drew one,
with the comparison exiled to a second card further down the screen. Pinning is now visible
where you pin.

**How it's drawn is your choice, and every choice says what it costs.** Under the chart, "How
it's drawn" — closed, it prints the current answer; open, it is five decisions. *Shape*: a line,
a filled line, steps, or bare dots — and the difference is stated, because steps hold each day's
value until the next one and claim nothing in between, while a line runs straight through days
you never logged. *7-day average*: off, dashed behind the daily line, or the only thing drawn —
smoother, and a single terrible day disappears into it. *Days you didn't log*: joined up, or left
as a gap. *Several ratings*: together on one axis where heights are comparable, or one chart each
when four lines become spaghetti. *Rating axis*: the full 1–10, or fitted to the range you
actually scored — and while that one is on, the chart prints "axis fitted to 3–9 of 1–10, so
differences look bigger than they are", because an axis that starts at 3 flatters a flat
fortnight into a mountain range and nobody reads axis labels. The choices are saved with your
pins, so the chart opens tomorrow the way you left it. Underneath, the same metric averaged into
weeks or into months, with the number of days behind each bar on touch.

**Possible relationships.** Pick something you're tracking and something you suspect; the screen
compares the days both were logged, same-day or with a one-day lag. The two pickers are the
app's own control rather than a native `<select>` — the list runs to two dozen metrics, so it
opens in the same sheet everything else in the app opens in, with ratings grouped apart from
things measured their own way, each option saying what it is measured in, and a filter field
once the list stops being scannable at a glance. This is the most dangerous
screen in the app, and the danger was never bad arithmetic — it is reading "dairy 0.42" as "dairy
is doing this to me" and changing what you eat on the strength of eleven days. So the restraint
is in the code: nothing appears below twelve paired days (absent, not greyed out, with a line
saying how many more it needs); the sample size is printed *above* the result; it is Spearman's
rank correlation with ties averaged, not Pearson's, because these are ratings a person assigned
to their own body and the intervals between them are not equal; "strong" is unavailable below
thirty pairs however large the coefficient; the default shape is a grouped comparison rather than
a scatter, because "on the days you logged more of this, that averaged 6.8 rather than 5.4" is a
sentence you can act on carefully and a cloud of dots with a coefficient is one you will act on
confidently; and "not proof that one causes the other" is on screen at all times.

**The day around the day (optional, off by default).** A journal that only holds what you typed
is missing the half of your life that happened to you. Switch on daily context and every day
quietly gets the weather attached: temperature, humidity, barometric pressure *and its change*,
conditions, UV index, sunrise and sunset, daylight duration, air quality, PM2.5 and PM10, and
pollen where it's published. Two rules make that safe to have. Your coordinates are rounded to
about a kilometre **before** anything is written down or sent, in one function, once — what's
stored is a reading of the sky, not a record of where you were, and the export column is called
`latitude_coarse` because that's all there ever was. And it stays invisible until it means
something: behind a day as a wash whose loudness comes from how unusual that day was against
*your own* range, as a temperature trace above your recent days, and — only when it has something
to say — as a count of your own days. *8 of your 10 hardest days were above 29°C.* Never a
coefficient, never below twenty days of overlap, never a cause. The settings card lists exactly
what is sent and what comes back, in enough detail to check against a network tab, and turning it
off stops the requests immediately.

**Sun & Outdoor Light.** One tap starts a session, and what opens is drawn from the sun's own
arithmetic rather than from an illustration: the curve is the real solar elevation at your
latitude on today's date, the shaded band is where there's enough UVB for synthesis to be
plausible, the thicker overlay is the part you've spent outside, and the disc is where the sun is
now. It looks flat and bandless in December because December is. Alongside it run a stopwatch,
live UV (a forecast value where there is one, a modelled clear-sky value otherwise — the screen
says which), the sun's height and bearing, minutes outside, ambient UV dose in SED, and
**estimated vitamin D: ~1,800–2,600 IU, research-model estimate · not a measurement.**
Personalised on the UV over your actual session, latitude, date, skin type, age, exposed body
area, clothing, sunscreen and shade, printed as a range because the honest width of the estimate
is wider than any single number implies, with every assumption listed one tap away. The model
plateaus rather than climbing, because past about one minimal erythemal dose your skin stops
making more — an app whose number keeps rising is telling you a longer burn is a bigger benefit.
Beside it runs the burn scale, the only element on the screen allowed to change colour, and the
atmosphere behind the whole screen warms with it. Also kept: first outdoor light after waking
(a circadian number, deliberately separate from anything about vitamin D), the best upcoming
window, and the next vitamin-D-producing one — which correctly says *none in the next week* in a
British January instead of inventing one.

**A session you can walk away from, and one that ends itself.** The reason time-outside tracking
fails is not starting — it is stopping. Starting is one tap on the way out of a door; stopping is
a chore you will forget on the day you feel worst. So the session no longer belongs to the screen
it was started on: leave it, lock the phone, close the app entirely, come back an hour later, and
it is still running, with a live row on Today counting up and one tap back to it. **It ends when
you end it.** And if you say so, it ends when you head in — your phone can tell roughly when it
stops seeing open sky, because a position fix that resolved to eight metres under the sky reports
sixty or ninety under a roof, and the session closes at the moment the fixes changed rather than
whenever the app worked it out. It reads **how accurate its own position is, not where you are** —
no coordinate ever reaches that model, which is a guarantee a test enforces rather than a claim
this file makes. A session it closed is saved immediately, marked as the app's own estimate, and
asks one question the next time you look: *is that about right?* One tap accepts it, a slider
corrects it — and correcting it recomputes the dose and the vitamin D range over the new window
rather than relabelling the old one. Ignoring the question forever is a valid answer: the session
stays on your timeline, permanently labelled an estimate. One left running for six hours closes
itself at the last moment it could honestly still have been sunlight — a session begun at 8pm and
forgotten closes at sundown, not at 2am — and says out loud that the time is a guess. All of it is
one switch in **Settings → Automations**, which lists every automation in the app beside the three
things that make a switch mean anything: what it *watches*, what it *writes*, and how you *undo*
it. Nothing any of them does leaves the device. [The full map, including what was deliberately
rejected.](docs/AUTOMATION.md)

**Personal experiments.** *Does morning sunlight relate to better sleep? Does humidity line up
with my eczema? Did anything change after I started this cream?* Ask, and the app builds the
smallest comparison that could answer it — from a list of real questions in plain words, from its
own suggestions once you have the history for one, or from a picker that can put anything against
anything: a symptom against the pollen count, a meal against the next morning, a lab value against
a season. Your days are split at **your own median**, so both halves exist; the ladder grades on
the smaller half, because fifty days with two above the line is two days of evidence in fifty
days' clothing. And nothing is reported until the ladder allows it. *Collecting* is a progress bar
and a count — not a hedged result, because a sentence with a caveat on it is still a sentence you
will remember. Then *Emerging: something may be forming.* Then *Useful: on days with 15 min+ time
outside, your sleep quality has averaged 0.9 points higher.* Underneath, every paired day is a dot
placed by its own two values, split at the threshold, with each half's average drawn as the level
its dots sit around — two clouds at different heights *is* the finding, and overlapping clouds is
the null result, drawn identically, because the app is not more excited about a positive.

**One ladder for everything the app claims.** *Useful* on an experiment and *Useful* on an insight
are now the same claim about the same kind of evidence: four rungs counted in paired days and in
how far they're spread. Forty days from a single fortnight is capped at Emerging however clean it
looks. There are no confidence percentages anywhere — a percentage is a promise about a
population, and this is a sample of one with no control group. **Why am I seeing this?** opens the
working instead: usable observations, days missing one side, the comparison window, how the days
were split, consistency, the lag used, and the limitations — including the three that are true of
every finding this app can ever make.

**Labs & measurements.** Vitamin D, ferritin, HbA1c, TSH, B12, cholesterol, blood pressure,
weight, or anything at all with a name and a number. Each result keeps its value, unit, date and
time, **the reference range your laboratory printed**, fasting status, provider, a note and a
photo of the report. That range is the whole point: ranges differ between labs, assays and
countries, so a result recorded without one gets no band, no colour and no verdict — this app
does not know what normal is for somebody else's assay. A new value arrives *into* its history:
the line reaches back from the previous reading, the delta counts up beside it (*38 ng/mL, up 14
over 92 days*), and the band underneath fills in with what else your journal held during the gap —
☀ time outside increased, ◍ a supplement started, ▲ a flare, ❈ the season turned — with the line
that says this is a memory aid and not an explanation. Where the test is 25(OH)D, your measured
blood level sits beside the estimated production from sunlight over the eight weeks before the
draw: two panels, two units, two headings, one solid border and one dashed. Never one axis.

**Tap a finding, and the days light up everywhere.** A coincidence on Insights, an experiment's
half, a lab period, a flare — tap any of them and *those exact days* illuminate: History reorders
itself to show them, the temperature trace behind them marks them, and so does the thirty-day sun
history. One set of days, one banner naming what lit them, one Clear, surviving navigation.
Sunlight is experiment data; weather is context on every day; labs are timeline events with your
journal drawn underneath them; flares shade the charts and can illuminate their own fortnight.
One connected memory rather than five separate features.

**Your year, on one screen.** Under the 30-day chart sits the whole last twelve months of the
selected 1–10 metric: one row per month, one square per day, a distinct shade for every score
from 1 to 10, and nothing at all on the days you didn't log. It is months-as-rows rather than the
usual weeks-as-columns for a plain reason — a phone gives a card about 330px, which is 5px per
day laid out by week and 9px laid out by day-of-month. Squares that small are not a tap target,
so a tap *names* the day in a readout under the grid, next to the button that opens it: landing
on the 14th when you meant the 15th is something you can see rather than a screen you have to
back out of. The grid is one tab stop with arrow-key movement, every square says its date and
score out loud, and a month-by-month table underneath states the same figures in words for
anyone who can't use colour.

**Designed, not just built.** *Soft Clinical* — soft graphite in the dark, warm off-white in
the light, muted blue with sage, lavender and clay accents, generous spacing and quiet depth —
with a deliberate hint of neobrutalism: borders a notch above a hairline, hard offset shadows,
chunky buttons that press down into them, and section titles you can find at a glance. Calm, not
loud.

**Built for one thumb.** Sheets rise from the bottom edge and stay welded to it, so their action
row is the closest thing on screen to the thumb rather than the furthest. They are sized in
`dvh` — `vh` on iOS Safari means the viewport *without* the URL bar, which is how a web form
ends up hiding its own Save button — and they get out of the keyboard's way on both engines:
Chromium via `interactive-widget=resizes-content`, iOS Safari via a `visualViewport` listener,
both feeding one CSS variable. A sheet dismisses on Escape, on a tap outside, and on a downward
drag of its heading.

Long forms use progressive disclosure, and the closed rows state their own answers — "Medium ·
Brown", not "More options" — so folding a section away hides the controls and never the
information. Everything the everyday path doesn't need is one tap down: the bowel sheet went
from about 1,500px of scrolling to a single screen, and Bristol type is drawn as the ordered
scale it actually is rather than seven stacked paragraphs.

**Dark, light and Night Light.** Dark by default, with a light theme that's a proper design
rather than an inversion, and a "match system" option. The choice is remembered on the device and
applied before the first paint, so a cold start never flashes white. **Night Light** takes the
blue out of every colour the app paints — a transform of the pixels, not a warm sheet laid over
the top — and pulls the accent into the amber band with them.

**A colour of your own.** A horizontal hue slider re-tints buttons, charts, focus rings and the
backdrop. The accent is *solved* rather than picked: the app walks lightness until the pair
actually measures at WCAG AA, so every one of the 360 positions clears the same bar the shipped
blue did. `tests/theme.test.ts` checks the whole wheel in both themes with Night Light on and
off, and fails the build if any token pair drops below AA. The semantic colours — the severity
ramp, and the hues that tell a food card from a bowel card — deliberately don't move with it.

**Backdrops that appear.** Fog or Aurora, in CSS: no WebGL, no canvas, no device test, nothing to
feature-detect. Chosen on the first launch alongside the colour and theme, so the rest of setup
runs wearing the choice.

**AI (optional, off by default).** One integration, five uses: possible patterns, food from
text, food from a photo, food from both, and bowel-photo attributes. Every one of them shows you
exactly what is about to be sent and waits for you to confirm — nothing is sent on save, in the
background, or on a retry without asking again. With AI switched off there is no analysis button
anywhere and the app makes no network request at all.

Bring your own Google Gemini API key and the
Possible Patterns section gains a second, clearly-labelled source: longitudinal observations a
median split doesn't look for — symptoms that recur together, changes after certain days,
sleep/mood relationships, timing patterns, drifts from your own baseline. Every finding carries
its evidence, an in-plain-words strength, a date range, and a "why this was suggested"
disclosure, and can be dismissed. Nothing runs automatically, nothing is sent without a preview
you confirm, and only numeric answers go — never notes, photos, or your name. Locally
calculated patterns stay exactly as they were and keep working with no key at all.

**Photo progress.** In-app camera with a self-timer, per-body-area tracking, thumbnails, an
A/B comparison slider, and baseline pinning. Photos are blobs in local storage — they never
upload.

**A finish that tells the truth.** Skipping every question in a check-in used to end in
confetti and a streak count — the app congratulating somebody for a blank day. The celebration
is now earned by an actual value, note or photo; without one you get "Nothing logged yet", the
way back, and the main number right there, because one tap is enough to make it untrue. A day
with nothing in it is not written to the journal at all, so it never appears on the calendar, in
a streak, or in an export. And Skip no longer erases: it means "don't ask me these", not "delete
what I already answered".

**Weekly and monthly reports.** Swipe to choose which card types you want, then browse any
period with arrows or a horizontal swipe. Save up to 24 reports to history, share one as an
image, or **print it** — the printed version is a clean, self-contained document with its own
masthead and disclaimer, meant to be handed to a clinician.

**The appointment pack.** Ten minutes with a specialist every few months is what all of this is
for, and the question that opens it — *"so how have you been?"* — is the one memory answers
worst: it reaches for the last bad week, because that is what memory does. So the first thing on
the Export screen, above the three file formats, is **Prepare an Appointment Pack**. Choose a
window — the last 30 days, three months, your own dates, or **since my last appointment** — and
one tap produces one or two printed pages in the order a consultation actually runs: the average
and which way it moved against the same number of days before it, how many days it rests on, your
best, hardest and most common day, how many flares there were and how long they ran and how bad
they got, the three metrics that moved the most, what you took against what the plan asked for, a
before-and-after photo pair, the notes you picked out yourself, and — last, because it is the part
that belongs to you rather than to the app — **your own questions, printed with a rule under each
one so there is somewhere to write the answer down.**

Every section can be switched off, every average carries the coverage behind it, and a figure with
nothing behind it is left out with its reason shown in the app rather than printed as a zero.
Nothing is chosen for you: which notes a doctor reads, and which photos, are decisions the app
declines to make on your behalf.

<a id="search"></a>

**Search — one box over the whole journal.** A journal kept for a year is a filing cabinet, and
for a long time this app gave you no way into it. *When did I last take the antihistamine? What
did I eat the week of the flare? Which days was the itch a 9?* All three had the same answer,
which was to scroll History with your thumb and hope.

One field, and everything is in it: every note you have written, every meal, dose, bowel entry,
ritual, flare, lab result and hour outside, the saved foods and routine items themselves, the
questions your survey asks, and the screens — because *"where is the backup button"* is a search
somebody makes, and `backup` finds Export. It answers on the **first keystroke** (the index is
built once from the journal already in memory, so there is nothing to wait for), and **every
result opens the thing it found, on the day it happened** — a meal from March opens the Diary in
March. It is one tap from Today, one tap from History, in the header of every screen that has
one, and in the fan.

Plain words are the overwhelming majority of searches and always work. On top of them sit five
things people already type into search boxes elsewhere:

| | |
|---|---|
| `"woke at 4"` | that exact phrase |
| `-coffee` | leave out anything that mentions it |
| `is:meals` | one kind only — days, meals, doses, bowel, rituals, flares, labs, sun, questions, screens |
| `on:yesterday` `after:2026-08-01` `last:30d` | a day, or a stretch |
| `pain>7` | **days where a question you are asked went over a number** |

That last one is the one a symptom journal actually needed — `itch>=8 -dairy` is a real question
with a real answer, and asking it used to mean exporting a spreadsheet.

Nothing is ever rejected: a token that looks like a filter and is not one is treated as a word, so
a stray colon never costs you your search. Every filter that *did* parse is shown back to you as a
chip, because the commonest failed search is one with a filter you forgot was on and "no results"
cannot tell you that. A comparison against a question your journal does not ask says so by name
rather than quietly returning nothing. And every term has to match — `havarti cheese` finds the
hamburger, not every meal containing either word.

The empty screen is five searches you might actually want to run, each one tap from running, with
the operator reference folded underneath. All of it is local: an index built in memory over data
already on your device and thrown away when you close the screen. This is the exact opposite of
the import path — it sends nothing, ever.

**Get your data out.** CSV, multi-sheet Excel, and JSON — with date-range filters — plus a full
JSON backup including photos that restores on any device. In a browser they download; on the phone
app they go to the share sheet, so *Save to Files*, mail or AirDrop are all one tap, and where the
file ends up is your choice rather than the app's.

**Reminders.** On the phone app, your phone schedules them itself: they arrive at their times with
it closed, and nothing is sent anywhere to make that happen — no push service, no account, no
identifier. Everywhere else, a repeating calendar file does the same job, and browser
notifications are offered on top with an honest note that they only fire while the app is running.

**Extras.** Optional 4-digit app lock. Wearable import from a Google Fit / Fitbit Takeout
export. A read-only web viewer for opening a backup on a desktop. An iOS Home Screen widget
(needs a Mac to finish building).

---

## Try it

```bash
npm install
npm run dev
```

Open the printed URL (usually `http://localhost:5173`) and use a mobile viewport (~390px) —
the app is designed phone-first.

First run shows the whole flow. To jump straight into a fully populated app, pick
**"Look around with example data"** — an Eczema/Skin + Carnivore setup with ~34 days of
history, enough to exercise the dashboard, charts, calendar, patterns, reports, and exports.

| Command | What it does |
|---|---|
| `npm run dev` | Dev server with hot reload |
| `npm run build` | Production build to `dist/` |
| `npm run preview` | Serve the production build |
| `npm run typecheck` | TypeScript over `src/lib`, `src/components`, `src/types` |
| `npm run test` | Vitest: pure-function suites + full-app jsdom render tests |
| `npm run check` | typecheck + test + build, in that order — what CI runs |

---

## Deploying it

Everything is client-side, so "deploying" means serving a folder of static files.

**GitHub Pages** is wired up. The `pages.yml` workflow builds and publishes on every push to
`main`, and reads the real Pages base path, so a project site at `user.github.io/bellwether/`
works without editing anything.

It needs **one manual switch, once**: go to **Settings → Pages** and set **Source** to
**GitHub Actions**. Creating a Pages site requires admin rights that the workflow's built-in
token does not have, so the deploy fails with *"Resource not accessible by integration"* until a
human does this. After that, every push deploys on its own — re-run the failed job or push
anything to `main` to publish the first time.

**Anywhere else** (Netlify, Vercel, Cloudflare Pages, your own server):

```bash
npm run build          # -> dist/
BASE_PATH=/sub/path/ npm run build   # if it won't sit at the domain root
SITE_URL=https://example.com npm run build   # absolute URLs in link previews
```

Then serve `dist/`. Serve it over HTTPS if you want the PWA install prompt and offline mode.

Two workflows guard the repo: `ci.yml` runs `npm run check` on every push and PR, and
`ios-build.yml` compiles the native iOS wrapper on a macOS runner.

---

## Install it on a phone

Open the deployed site on your phone and choose **Add to Home Screen**. It then launches
full-screen, works offline, and gets Home Screen shortcuts straight into today's log or this
week's report.

Installing is also the most reliable way to keep your journal: browsers evict storage for
sites you haven't visited, and iOS Safari does so after about a week. See below.

**[docs/PHONE.md](docs/PHONE.md)** is the whole thing step by step, from a fresh clone to an
icon on a Home Screen — the four paths (Home Screen web app, a native build on your own iPhone,
TestFlight, the App Store), what each one costs and gives you, how to verify at each stage, and
what to do when it goes wrong.

---

## Where your data lives, and how to not lose it

Your journal is written to this browser's IndexedDB (`src/lib/storage.ts`, which also polyfills
the Claude artifact `window.storage` API so the same `App.tsx` runs in both places). Photos are
blobs in the same store. Nothing is uploaded, because there is nothing to upload it to.

The flip side is that **nobody can recover it for you**. Three things protect you, in order of
how much they help:

1. **Save a backup file.** Settings → Backup & storage → *Full backup*. It's an ordinary `.json`
   on your device that restores everything, photos included. Insights nudges you when your
   journal has drifted too long since the last one.
2. **Install to the Home Screen.** Installed apps are exempt from the idle-eviction rules that
   clear ordinary sites.
3. **Let the app ask for persistent storage.** It requests this automatically; Settings shows
   whether the browser granted it, with a manual button if not.

Clearing site data by hand still erases everything. Export a backup first.

### Optional sync across devices

**Off by default. Local Only is the product; this is an option.** No account is needed, nothing
is uploaded, and every word above stays true unless you turn this on yourself.

Turned on, it does one thing: log something on your phone, open the app on your computer, and
it's already there. Edit it there and the change comes back. Settings shows two words — *Local
only* or *Synced* — and the setup is four screens: what this does, a code emailed to you, a
passphrase, done. There is no password to invent, and the words *database*, *bucket* and *token*
appear nowhere a normal user can see them.

**Local saves never wait for the network.** The journal is written to disk on the same debounce
it always used, and the sync engine finds out afterwards. No signal, expired session, server
down, laptop lid closed mid-push — none of it can reach the save path.

What that costs to build, and what it buys:

| Problem | How it's solved |
| --- | --- |
| Two devices both log Tuesday | A day's sync identity is its **date**, not the random local id each device minted. One Tuesday, always. |
| Two devices edit the same day | Entries merge **answer by answer**. A phone recording pain at breakfast and a laptop recording sleep at midnight are not in conflict, and last-write-wins would throw one away. |
| A deletion gets undone by the other device | Deletions are **tombstones** in the journal itself, so they survive a reload and travel like any other change. Undo lifts the tombstone too. |
| A pull silently skips a row | The cursor rides a **server sequence**, not a timestamp. Two rows written in the same millisecond can't slip through the gap. |
| A request that may or may not have arrived | Pushes are **idempotent** — the server keeps the newer of two versions — so retrying is always safe. |
| A device that's been offline for a week | The conflict rule is enforced **in SQL**, not only on the client, so a stale write is dropped by the server. |
| Both sides already have a journal | The first pass is a **union**. Every day from both devices survives; neither side is overwritten. |
| Photos are enormous | **Separate opt-in.** Sync your entries without paying for a year of daily photos on a metered connection. |

Everything you wrote crosses: days, meals, bowel entries, the food library, the routine and its
doses, **rituals, their daily runs and their weekly tune-ups**, sun sessions, lab results,
experiments, flares, and the day's weather. Two devices that disagreed about whether you had done
this morning's ritual would be two journals, not one. A ritual run is identified by *which ritual
on which day* rather than by the id whichever device asked first happened to mint — otherwise a
week ticked on both a phone and a tablet reads as fourteen days and doubles its own streak.

What stays home is what describes a machine rather than a journal: sound and haptics, the AI
connection, notification permission, and when *this* device last downloaded a backup.

#### What the encryption does and doesn't claim

Every record's contents are sealed on your device with **AES-256-GCM**, under a key derived by
**PBKDF2-SHA256 at 600,000 iterations** (OWASP's current figure) from a passphrase that is never
transmitted. The ciphertext is bound to the row it belongs to, so it can't be moved between
records without failing to decrypt. The server holds a kind, an id, a timestamp, a device id, a
deleted flag — and blocks it cannot read. The derived key is stored **non-extractable** in
IndexedDB, so the passphrase is never written down anywhere and the key can't be read back out
as bytes by any code, including this app's.

What is deliberately **not** claimed, in the app or here:

- **Not zero-knowledge.** The app is delivered over the web. Whoever controls the host controls
  the code that handles your passphrase. That's true of every browser-delivered encrypted app,
  and saying so is more useful than a badge implying otherwise.
- **Not HIPAA, not "medical grade".** No compliance posture is claimed anywhere in this project.
- **Not protection against someone holding your unlocked phone.** The local journal is plaintext
  on the device — that's what makes it instant and offline-first.

Losing the passphrase means the synced copy can't be read again. The copy on your device is
unaffected, and a downloaded backup still survives everything.

#### Pointing it at a server

This repository ships no server and no credentials, because a shared one would mean strangers'
health journals landing in an account nobody owns. Sync becomes available when a Supabase project
is configured, in either of two ways:

1. **For a deployment.** Set the repository secrets `VITE_SUPABASE_URL` and
   `VITE_SUPABASE_ANON_KEY`; the Pages workflow passes them to the build.
2. **For one device.** Settings → Sync across devices → *Use your own sync server*, and paste the
   two values.

Either way: create a project, open its SQL editor, and run [`supabase/schema.sql`](supabase/schema.sql)
— it creates the tables, the row-level security policies, the conflict rule, the realtime
publication, and the private photo bucket, and it's safe to re-run.

The **anon key is meant to be public**: it identifies the project and authorises nothing on its
own, because every table is restricted to the signed-in owner. The **service-role key bypasses
all of that** and must never be added to this repository, the build, or a browser.

With neither source set, `syncConfig()` returns null, Settings says so in one plain sentence, and
the app is exactly the local-first journal it has always been.

### Optional AI observations, and your API key

Off by default, and everything else works identically whether it's on or off.

Setup is a **five-step guided walkthrough** launched by one button on Insights — you never
have to work out what to do next, and you never leave the screen you started on:

1. **What it does**, and exactly what would and wouldn't leave the device.
2. **Choose a provider** (below). Gemini is preselected as the shortest path.
3. **Get a key** — opens that provider's console in a new tab, with the things to click on that
   page written out, because "create an API key" is where most people stop.
4. **Paste it** — verified the moment it's pasted. Continue stays disabled until it checks out
   (with an explicit override so a flaky connection isn't a dead end).
5. **Review and run** — the exact payload, then the analysis, landing straight on the results.

**Settings → AI observations** manages it afterwards (test, replace, remove); replacing runs the
same guided flow rather than a second, subtly different form.

#### Which providers, and why not ChatGPT

This app has no backend, so every request goes straight from your browser to the provider. That
makes browser CORS support a hard requirement, not a preference:

| Provider | Free tier | Notes |
|---|---|---|
| **Google Gemini** | Yes, no card | The default. Keys start `AQ.` (older ones `AIza`); both work. |
| **OpenRouter** | Free models, no card | OpenAI-compatible; one key reaches many makers' models. |
| **Anything OpenAI-compatible** | Depends | Groq, Mistral, or a model on your own machine — you supply the endpoint. |

**OpenAI (ChatGPT) is not on that list**, and the app says so in the picker rather than letting
you find out the hard way: their API sends no CORS headers, so calling it from a web page is
impossible without a server to relay through — which is the one thing this app refuses to have.
OpenRouter can reach OpenAI's models on your behalf if you want them.

#### No model ID is load-bearing

The first version hard-coded `gemini-2.5-flash`. Google retired it for newly-created keys months
ahead of the published shutdown date, and every new user got a 404 from a build that had worked
the week before. So models are never assumed:

- **Setup asks your key what it can reach** (`GET /models`) and scores the results — newer over
  older, small and fast over frontier, free over paid, stable over preview. One round trip
  proves the endpoint is reachable, the browser is allowed to call it, the key is accepted, *and*
  something usable sits behind it.
- **A model that disappears repairs itself.** If a request comes back "no longer available", the
  app re-resolves from the live list, retries once, and remembers the new choice. Exactly one
  retry — a broken provider shouldn't become a loop.

#### What leaves the device

**For the pattern analysis**, only after you confirm a preview that spells it out:

- the labels of the metrics you track, and
- one row per logged day of **numeric answers** in the window, with days numbered from the start
  of the window rather than dated.

What never leaves *on that path*: written notes, photos, your name, anything identifying, any
entry outside the window, and any question you've excluded from charts. `tests/ai.test.ts`
asserts each of those.

There is exactly one path that sends prose, and it is the one whose entire input is prose —
importing your own notes, below. It is a separate button, it asks every time, and it lists the
whole payload before it sends anything. Nothing else in the app can put your writing on a wire.

#### Import your own notes

The one feature that exists only because the AI does, and the only one in the app that sends
free text.

Everybody who tracks anything seriously was already tracking it before they found this app — in
a notes file, a chat with themselves, a photo of a page. It looks like `8.21 weight 12pm 182`,
`2acv premeal + 2 pepsin combo 12:30pm`, `8.21 4pm bowel movement, small firm sank`. Every one of
those lines is a row this app already has a shape for, and typing them in one at a time through
the right sheet on the right date is an hour of work nobody does.

So: **Import notes** takes a paste or a screenshot, and reads it into meals, doses, numbers,
bowel entries and notes — **on the dates and times the notes themselves give**, not today's.
Shorthand dates are resolved against today; a line with no date of its own belongs to the line
above it; a time is only set when the note actually gives one. A dose matches something already
in your routine where it can, and creates it where it cannot.

**And it reads a paragraph just as carefully as a log.** The person with the tidy dated file
exists; so does the one who never kept one and would describe the last fortnight in three
sentences if asked. *"Started 10mg amitriptyline last Tuesday, every night since. Sleep has been
about a 4 most nights. Cut dairy on the 12th and the itch is better — a 3 today, was a 7."* is a
course of a medication, a rating, a change and a rating today, and all four come back as rows on
the days they belong to.

- **A stretch of days is one row that writes many.** "Every night since Tuesday" is eight doses,
  and filing it as one dose on Tuesday would disagree with the notes it was handed. It stays
  **one row in the review** — a fortnight of a nightly tablet taking fourteen lines would make
  the list unreadable — marked with how many days it covers, and writes one record per day when
  you approve it. Correcting its first date moves the whole stretch, because the length is what
  your notes said and only the position was wrong.
- **It will never do that to a rating or a bowel movement.** "About a 4 most nights" is *one*
  answer with a caveat saying so. Six invented fours would be six points your charts then draw.
- **It asks, and it answers itself.** Real notes are ambiguous — two things with the same short
  name, a course with no stated end. A reader that stopped and asked would have turned a paste
  into an interrogation, so it decides, files every row under the decision, and hands back the
  question *with the answer it used already marked*. Ignore it entirely and you still get a
  complete, honest plan. Change one and the notes are read again around your answer — which is a
  second request, so it asks before it sends, exactly like the first.

**Getting your notes in** is deliberately whatever is nearest to hand:

- **Paste them** into the box. Shorthand is fine — that is the point.
- **Ctrl+V a screenshot straight into the box.** On a desktop that is where your notes already
  are, one keystroke after the snip, and making you save a file first would put the friction
  back.
- **Drop files anywhere on the screen** — images, or a `.txt` / `.md` file, which is appended to
  the box rather than making you open it and copy it out.
- **Pick up to four screenshots at once.** A chat with yourself is four screenshots, not one, and
  they are sent as *one continuous document in order*, so a date at the top of the second still
  governs the lines under it in the third. Past four, run it again — the duplicate check makes
  that free.

**Finding it** is three doors, in the order somebody actually needs them. A journal in its first
fortnight is offered it **on Today**, under the day, because that is the week it matters and
nobody in their first week goes looking through menus. It retires itself after fourteen logged
days whether or not you dismissed it, "Not for me" sends it away permanently, and when AI is off
the card says so in its own words and its button goes to Settings — an offer that quietly turns
into a setup screen is a bait, and this app doesn't have any. It also lives in the **+** sheet
and in **Settings** for as long as you want it.

Three steps, and the shape of them is the safety argument:

1. **Hand it over** — paste the text, or pick a screenshot.
2. **See what goes** — nothing leaves until a sheet listing the entire payload has been read and
   accepted, every time. It counts the characters, says whether an image is going, and names the
   structural things that ride along (your question names, your routine names, today's date). No
   photos from your journal, no answers you have already recorded, no name, nothing about the
   device.
3. **Approve what lands** — every proposed row, grouped by the day it would go on, **beside the
   words it was read from**, because a wrong reading is obvious the instant it sits next to what
   it claims to be a reading of. A header line says what was found (*1 answer, 1 meal, 1 bowel
   entry, 1 dose and 1 note, on 2 days*), each day can be switched off in one tap, each row's
   date can be corrected on the row, and anything the model was genuinely unsure of is flagged —
   only that, because a badge on every row is a badge on nothing. Then one button writes what is
   left, with an Undo in the toast and a link straight to the earliest day it just filled in.

   Two things the review learned to say **before** the button rather than in the receipt after
   it. **"Already in your journal"** — it runs the exact function the commit will run against
   your real journal and marks the rows that would be skipped, with one tap to switch them all
   off, because running the same notes twice is what everybody does when the first run was a
   test. And **what this journal had nowhere to put**: a blood pressure reading with no blood
   pressure question used to vanish silently between your notes and the review. It is listed
   now, in the words it came from. A list that is quietly shorter than the notes it was made
   from is the one outcome that makes somebody stop trusting the whole feature.

The model never writes. `applyImport` is a pure function of the rows you approved and has never
heard of a model; `normaliseImportPlan` is the boundary in front of it and drops anything it
cannot vouch for — an answer to a question your journal does not ask, a value of the wrong type,
a routine id that does not exist, a date in the future or three years adrift, a caveat that
strayed into diagnosis. It never overwrites an answer you gave yourself, and running the same
notes through twice does not file anything twice. A routine item invented from a note is created
as **as-needed**, never as a daily obligation — a line saying you took something once is not a
line saying you take it every morning. `tests/import.test.ts` and `tests/importUi.test.tsx`
assert each of those, including that nothing reaches the network before the sheet is accepted.

The key is stored under its own storage key, outside the journal object, so it cannot end up in
an export or a backup — the same arrangement as the PIN record. You can add, replace, test, and
remove it, and choose between remembering it on the device and holding it only for the session.
Settings states the limitation plainly rather than implying a vault: **a locally stored key is
not encrypted and cannot be**, because a local-first app has no secret to encrypt it with that
someone holding your unlocked device wouldn't also have. Revoking the key at your provider is
what actually stops it working.

Findings are phrased as observations, never conclusions, and output that ignores that
instruction is softened on the way in (`scrubCausalLanguage`) rather than rendered as-is.
AI-generated cards are visually distinct from the locally calculated ones at a glance.

### Optional PIN lock

Off by default — the app opens straight to your journal. If the device is ever shared, turn on
a 4-digit PIN in **Settings → App lock**. It re-locks whenever the app is backgrounded, and only
a salted SHA-256 hash is stored (`src/lib/lock.ts`), in its own key that is never included in a
backup. Forgetting the PIN never locks you out: "Forgot your PIN?" removes the lock, not the
journal.

---

## Read-only backup viewer

The build ships a second page, **`/viewer.html`**. Drop a `.json` backup on it and browse the
dashboard, calendar, reports, photo comparisons, and exports with no ability to edit. It uses
isolated in-memory storage, never touches a journal already in that browser, and discards the
file when the tab closes. Useful for reviewing your journal on a desktop, or for handing a
backup to a partner or clinician along with the viewer link.

---

## Project layout

```
bellwether/
├── index.html / viewer.html    # two entry points
├── vite.config.ts              # base-path-aware build, PWA, chunking
├── src/
│   ├── main.tsx                # storage polyfill, mounts App
│   ├── App.tsx                 # the app (migrated single-file artifact)
│   ├── components/             # ambient backdrop, appearance panel, lock,
│   │                           #   recovery, viewer landing, metric picker,
│   │                           #   field select (the app's own dropdown),
│   │                           #   chart view controls (how it's drawn),
│   │                           #   year heatmap, score distribution, episode
│   │                           #   timeline, the trend/comparison chart,
│   │                           #   relationships explorer, long-term view,
│   │                           #   appointment pack (the printed page),
│   │                           #   first run (the doorway, six acts — one of
│   │                           #     them the question you came with — three
│   │                           #     walked one card at a time, a dated plan
│   │                           #     at the end, and the offer to bring in
│   │                           #     notes you already keep elsewhere),
│   │                           #   tour (being shown around the finished app,
│   │                           #     once, with the real controls spotlit),
│   │                           #   ai connect (the three-tap guided way to a
│   │                           #     free key, offered where it earns it),
│   │                           #   rail (the one horizontal scroller),
│   │                           #   search (one box over the whole journal),
│   │                           #   rituals (the day's card, the step player,
│   │                           #     the weekly tune-up, the manage screen)
│   ├── lib/
│   │   ├── theme.ts            # design tokens, dark/light/night, hue derivation,
│   │   │                       #   contrast solving
│   │   ├── ai.ts               # optional AI analysis (credential, payload, parsing)
│   │   ├── aiProviders.ts      # provider catalogue, model discovery + scoring
│   │   ├── storage.ts          # IndexedDB window.storage polyfill
│   │   ├── tracking.ts         # food + bowel logs, food library, goals, daily metrics
│   │   ├── routine.ts          # meds/supplements/creams/products: items, doses, checklist
│   │   ├── rituals.ts          # multi-step routines, runs, streaks, staggered weekly tune-ups
│   │   ├── metrics.ts          # the one registry of chartable derived metrics
│   │   ├── heatmap.ts          # the 12-month year grid, summaries and colour ramp
│   │   ├── distribution.ts     # days per score, the three middles, hard/calm counts
│   │   ├── episodes.ts         # the flare model + every number one can be asked for
│   │   ├── appointmentPack.ts  # the printable summary: figures, floors, what it refuses
│   │   ├── intro.ts            # the first-run choreography (hero, FLIP, timeline draw)
│   │   ├── aims.ts             # what somebody came to find out, what each aim
│   │   │                       #   suggests, and the dated plan it implies —
│   │   │                       #   evidence.ts's rungs at the cadence they chose
│   │   ├── pulse.ts            # the one-tap day, the question queue behind it,
│   │   │                       #   and which details to offer next
│   │   ├── tour.ts             # the stops of the one-off tour, what is behind
│   │   │                       #   the gear, and where each card sits
│   │   ├── import.ts           # reading somebody's own notes into rows (AI-only):
│   │   │                       #   prompt, boundary, and a pure writer. Reads a
│   │   │                       #   log or a paragraph; a stretch of days is one
│   │   │                       #   row that writes many; it decides rather than
│   │   │                       #   asking, and hands back the decision. The one
│   │   │                       #   outbound path whose payload is your writing
│   │   ├── search.ts           # one box over the whole journal: the index, a
│   │   │                       #   query language that never fails, the ranking.
│   │   │                       #   Pure, local, sends nothing
│   │   ├── quickActions.ts     # learned ordering + one-tap repeats, scored
│   │   ├── longterm.ts         # monthly averages, year-over-year, seasons, floors
│   │   ├── relationships.ts    # Spearman with ties, lag, coverage, sample floors
  │   ├── automation.ts       # the registry of everything the app concludes on
  │   │                       #   its own, and the contract all of it runs under
  │   ├── presence.ts         # indoors or outdoors, from how accurate the phone
  │   │                       #   says its own position is. Holds no coordinates
  │   ├── presenceWatch.ts    # the one file that touches a platform Position
│   │   ├── exports.ts          # typed CSV / wide-table generation
│   │   ├── questions.ts        # custom-question sanitising
│   │   ├── answers.ts          # type-safe answer read/write
│   │   ├── validate.ts         # runtime validation + causal-language audit
│   │   ├── lock.ts             # PIN hashing
│   │   ├── reminders.ts        # check-in times, .ics, browser notifications
│   │   ├── nativeReminders.ts  # the phone's own schedule, mirrored from the list
│   │   ├── saveFile.ts         # one way out for every file: download, or share sheet
│   │   ├── durability.ts       # persistent storage, backup freshness
│   │   ├── deeplink.ts         # ?screen= allowlist for Home Screen shortcuts
│   │   ├── chartView.ts        # how the trend chart is drawn (pure, saved)
│   │   ├── motion.ts           # Lenis + GSAP, and the scroll lock behind sheets
│   │   ├── sound.ts            # the synthesised instrument
│   │   ├── feedback.ts         # one door: haptics + sound + motion + visual
│   │   ├── sync/               # optional cross-device sync
│   │   │   ├── types.ts        #   the record contract
│   │   │   ├── merge.ts        #   conflict resolution (pure)
│   │   │   ├── project.ts      #   journal <-> records (pure)
│   │   │   ├── crypto.ts       #   PBKDF2 + AES-GCM sealing
│   │   │   ├── keyStore.ts     #   non-extractable key in IndexedDB
│   │   │   ├── backend.ts      #   the server contract + an in-memory one
│   │   │   ├── supabase.ts     #   the only file that knows what Supabase is
│   │   │   ├── config.ts       #   where the server address comes from
│   │   │   └── engine.ts       #   pull, merge, apply, push, retry
│   │   └── widgetBridge.ts     # iOS widget App Group bridge
│   ├── types/models.ts         # the data contract
│   └── styles/index.css
├── supabase/schema.sql         # sync tables, RLS policies, conflict rule
├── public/                     # icons, og-image.png, robots.txt
├── ios/                        # Capacitor wrapper + WidgetKit starter
├── docs/                       # APP_STATE, product plan, automation, widget setup, shipping
└── tests/                      # 1,616 tests across 65 suites
```

Colours are not written into components. `src/lib/theme.ts` owns two palettes and a live token
object that `App.tsx` reads as `C.something` at render time; a theme switch mutates it in place
and mirrors every token onto `:root` as a `--fhj-*` custom property, so the stylesheet and the
markup stay in sync from one source. `src/styles/index.css` holds the shared component classes
(buttons, chips, cards, segmented controls, switches, sheets, Quick Add tiles, timeline rows,
AI badges, empty states, skeletons) so screens compose rather than restating padding and hover
behaviour inline. The tactile treatment lives in two tokens — `--fhj-bw` and `--fhj-shadow-pop`
— plus one `.fhj-pop` class, which is why it can be turned up or down in one place.

`App.tsx` is deliberately still one file (its artifact heritage) under `// @ts-nocheck`, but the
data model lives in `src/types/models.ts` and is enforced at runtime by `src/lib/validate.ts`,
checked against live demo data in the tests. Modules are being lifted out of it one at a time —
`exports.ts` was first, and everything added since (`reminders`, `durability`, `deeplink`) is
fully typed from the start. Corrupted local data routes to a recovery screen that offers a
download before any reset, never a silent wipe.

## Motion and polish

- **Lenis** smooths wheel scrolling; touch stays native so mobile logging is never hijacked.
- **GSAP** drives screen transitions, the Quick Log finish moment, report card reveals, the
  setup wizard's per-step stagger, and the swipe-deck fling physics.
- **The ambient backdrop is CSS** — three blurred layers on the compositor, tinted live from
  `--fhj-hue`. Under `prefers-reduced-motion` it holds still rather than disappearing.
- **One feedback layer** (`src/lib/feedback.ts`). A call site names what the person did —
  `feedback("save")`, `feedback("error", { el })` — and four channels answer: haptics, sound,
  motion, and a visual acknowledgement on the element itself. On a phone with a Taptic Engine it
  drives real impact weights and notification patterns through Capacitor; everywhere else it
  falls back to scaled `navigator.vibrate` patterns; on a laptop with neither it still pulses the
  button, which is the one channel every user has.
- **Some sounds carry a position, not an event.** A rung on a 1–10 scale, a step in the setup
  wizard, and a digit on the keypad each pick their pitch from where they land in the series
  (`place("scale", 7, 10)`), so a 3 never sounds like an 8, typing a weight reads as a run, and
  the last setup screen resolves an octave above the first. One key throughout — F major
  pentatonic — so no two sounds in the app can clash.
- Every animation, sound, and haptic respects `prefers-reduced-motion` and the in-app toggles.
  Each channel degrades **independently**: sound off, haptics off, reduced motion, no motor, no
  audio device — each subtracts one and leaves the others working, and none of them can take a
  save down with it.
- Keyboard users get a skip link, a `main` landmark, visible focus rings, and `aria-current` on
  the active tab. `prefers-contrast: more` darkens text and card borders.
- The 30-day trend metric picker is a single tab stop with roving focus: ←/→/Home/End move
  between metrics, the selection is always scrolled into view, edge fades and arrows show that
  more exist, and a vertical wheel scrolls it horizontally on a desktop.
- Both themes are contrast-audited in CI (`tests/theme.test.ts`), and the severity ramp picks
  its own label colour by luminance so a swatch is never white-on-pale.
- Charts draw themselves in once and then hold still; under `prefers-reduced-motion` recharts
  renders the final frame directly.
- A confirmation sheet opening over a form makes that form `inert`, so its own buttons leave the
  tab order and the accessibility tree while the dialog asking about them is up.
- Overlays are exempt from the dashboard's entrance stagger. Sheets render as children of the
  screen that opened them, so they used to inherit its 240ms delay — the scrim arrived a quarter
  of a second after the sheet sitting on it had already slid up. Motion has to make the app feel
  faster, and that was the one place it did the opposite, on the most pressed path in the app.
- Undo is offered for anything reversible without loss — saving a log, deleting one, re-logging a
  favourite. It is deliberately *not* offered for the irreversible ones (clearing photos,
  restoring a backup over a journal), which keep their confirmation, because there is nothing to
  undo them with.
- **Nothing you tap is smaller than the thumb you tap it with.** `--fhj-tap` is 44px and, as of
  1.34, it is a floor in *both* directions — the earlier audit checked height and let width
  through, which is how the 1–10 scale this whole app is built around shipped as a row of 21px
  slivers on a 320px phone. All three of its scales are five across and two rows down now, the
  same shape the Quick Log always drew. Controls that could simply grow, grew; the handful whose
  ink has to stay small — an icon in a header, a "Manage" over a section — keep their size and
  take the tap on an invisible 44px box centred underneath (`.fhj-tap-floor`), so nothing moved
  and everything lands. Two things are deliberately exempt and both have a full-size route to
  the same place: a day cell in the year heatmap, and the arrows that nudge a chip row that also
  swipes. `tests/tapTargets.test.ts` holds the floor; the measurements behind it came from a real
  browser at 320px, because jsdom has no layout and would have passed the old code forever.
- The toast lives above the nav bar rather than at the top of the screen, for the same reason the
  sheet actions moved: the Undo inside it has to be reachable by the thumb that caused it. It
  never takes focus — it reports something that already happened.
- Back is in four places at once — the bar, the header, either side edge, and the phone's own
  back button — because a gesture nobody discovers costs nothing, and one somebody discovers
  should feel like the app was waiting for it. The destination fan has a keyboard route
  (`ArrowUp` on the +) and takes focus when it opens, so it is not a thumb-only feature.
- Tapping the tab you are already on returns to the top of it. A year of History is a very long
  page, and the alternative is the status bar — the one part of a phone a thumb cannot reach.

**On react-bits and Vanta.** [react-bits](https://github.com/DavidHDev/react-bits) was evaluated
and deliberately not adopted: it is a copy-in component gallery whose register — spotlight
cards, animated gradients, decrypting text — is louder than this product wants, and the handful
of interactions worth having (tactile press, card expansion, timeline reveal) are a dozen lines
of CSS each with no dependency and no bundle cost.

Vanta was adopted, and then removed in 1.7.0 for the same reason react-bits was never adopted.
It cost ~613KB of three.js, it needed a live WebGL context — so a driver blocklist, iOS Lockdown
Mode, or a context lost to a tab sleep left it silently blank — and it declined to start at all
on any device reporting fewer than 4 cores or under 4GB of RAM, which is a normal phone. The
feature was therefore absent for most of the people it shipped to, and no test noticed, because
no test asserted that anything appeared. What replaced it is three blurred `<span>`s and a
handful of keyframes, which is what the effect was always worth.

## Native iOS app + Home Screen widget

`ios/` holds a Capacitor-wrapped native project plus starter WidgetKit source
(`ios/BellwetherWidget/`) for a real Home Screen widget showing today's streak and key
metric — data reaches it via an on-device App Group, no network involved. Finishing it needs a
Mac and Xcode; see **[docs/WIDGET_SETUP.md](docs/WIDGET_SETUP.md)**.

**[docs/PHONE.md](docs/PHONE.md)** is the step-by-step route through all of this, start to
finish, and the place to begin if you just want the app on a phone.

Getting it onto other people's phones is a different question from building it, and it splits
in two. **[docs/SHIPPING.md](docs/SHIPPING.md)** covers the decisions — which distribution path
suits family and friends versus a public listing, whether an entity has to come first, and what
"legally covered" does and does not mean for a health app that gives no advice.
**[docs/APP_STORE.md](docs/APP_STORE.md)** is the mechanical half: the listing copy, the App
Privacy questionnaire answered field by field, and the review notes. `npm run check:store`
runs the submission preflight.

## Licence

No licence has been declared yet — that's the repository owner's call. Until one is added, the
default applies: all rights reserved.

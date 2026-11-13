# MVP design, version 2 (13 Nov 2026)

Why this exists: the founder tested the first build and asked for more. This file is the contract for that work.
It is prototype scope under `experiments/BRIEF-10.md` and amendment A-008. Everything personal stays under `data/`.

## 0. What the founder asked for (his words, shortened)

1. "Every 2 days" and "randomly" are missing. "Think of and implement all possible rules." Rules are "not always
   about timing": reminders, to-dos "and more".
2. Outputs beyond the message thread: email, calendar and "a bunch of output things".
3. "Sometimes it says that it can't find something but when I ask it again it finds it. That doesn't make sense."
4. The message must not say "Why". It should read like: "I've found some convenient chicken and rice recipes for
   you. I recommend this one [cite reel] because it only takes 15 minutes and requires just an instant pot. Here are
   the ingredients and the steps: … Alternatively, try these ones: … Or here's a wider selection: …". Images and
   embeds are welcome.
5. Picks "should lead to a final product". A "Beginner Modeling Tips" video sent for "mini Blender tutorials to start
   doing daily" does not.
6. Base answers on the person's own context: "how good are they at Blender?" Guess it from their library, then
   "have them validate it with a brief description of their direction during the setup". Get as much as possible
   during onboarding "so that everything after feels frictionless".
7. Recommendations from outside their history that are strongly related "could be really good too".
8. Onboarding should set up an export routine for Instagram and YouTube / My Activity, so they do not repeat the
   steps by hand.

Standing rules that do not change: the model fills forms and code acts; nothing is invented (every title, detail,
number and count shown must be backed by the item's own text or computed by code); friends' posts are never used;
captions are data, not instructions; no logged-in bot accounts and no scraping; keys only from the environment;
nothing personal in git; a repeating send needs a preview and a YES.

## 1. Rule model (schema.py, RuleSpec v 2)

A rule = when (trigger) × content (what) × do (where it goes), plus limits. Old v1 specs in a store must still load.

### when
```json
{"type": "now | once | schedule | random | on_request | new_items",
 "date": "YYYY-MM-DD", "time": "HH:MM", "in_minutes": 120,
 "days": ["MON"], "every_weeks": 1,
 "every_days": 2,
 "month_days": [1, 15, -1],
 "times": ["08:00", "20:00"],
 "window": ["18:00", "20:00"],
 "per": "day | week | month", "count": 3,
 "start": "YYYY-MM-DD", "until": "YYYY-MM-DD", "max_sends": 3}
```
- `once`: `in_minutes`, or `date` + `time`. Code works out the moment.
- `schedule`: exactly one cadence: weekly (`days`, `every_weeks` 1 to 8), interval (`every_days` 2 to 90, counted from
  `start` or the rule's creation date), or monthly (`month_days`, 1 to 31, -1 = last day; a day past the month's end
  means the last day). `times` holds 1 to 4 clock times (`time` stays as an alias for one). `window` in place of
  `times` means one send a day at a different minute inside the window.
- `random`: `count` sends per `per`, at random moments inside `window` (default 09:00 to 21:00), on `days` if given.
  "Randomly" with nothing else is 3 per week. The moments come from a seeded generator (seed = rule id + period), so
  they are stable across restarts and testable, and they are never shown to the person in advance.
- `on_request`: saved, run when asked. `new_items`: runs when the person's library gains items that fit (section 9).
- Limits on any repeating type: `start`, `until`, `max_sends`.
- `schedule.next_run(when, tz, after, anchor, seed)` stays the single place where times are computed, in UTC
  comparisons. `describe(when)` must read naturally for every form ("every 2 days at 8am", "on the 1st and 15th at
  9am", "about 3 times a week at random times", "twice a day, at 8am and 8pm, until 24 December").

### Person-level timing
- Quiet hours are per person (`people.quiet_start`, `quiet_end`; default 22 and 8), set by text ("don't message me
  before 10am").
- Snooze: "don't message me this weekend", "I'm away until the 20th" sets `people.snooze_until`; timed sends in that
  period are skipped and recorded (status `snoozed`). Asking still works.

### content
```json
{"source": "library | note | todos | recent",
 "text": "Call mum",
 "goal": "...", "searches": ["..."],
 "kinds": [], "platforms": [], "creators": [], "collections": [],
 "count": 1, "extract": ["ingredients", "steps"],
 "criteria": ["ends with a finished result", "suits a beginner"],
 "avoid": [], "since_days": null, "saved_after": null, "saved_before": null,
 "order": "best | newest | oldest | random | easiest_first",
 "outside": "none | some",
 "exclude_sent": true, "style": "full | brief"}
```
- `source`: `library` (search, as now); `note` (a plain reminder: `text` is sent as is, nothing is searched);
  `todos` (the person's open to-dos); `recent` (what they kept in the last `since_days`, newest first, no search).
- `extract` is a list (a v1 string still loads). `criteria`: up to 5 must-haves in plain words; the composer marks
  each yes / no / unknown per item, from the item's text only (section 3).
- `creators`, `collections`: filters matched in code against the item's creator and collection names.
- `order`: `random` is seeded per run; `easiest_first` tells the composer to choose by level, using the profile and
  how many this rule has already sent.
- `outside`: `some` adds a separate, labelled block of related things from outside the library (section 8).

### do (the action registry: actions/)
| Action | Params | What it does | Needs |
| --- | --- | --- | --- |
| `message.send` | none | The reply in the thread | nothing |
| `email.send` | none | The same answer as an email to the person's own verified address | a verified email |
| `calendar.add` | `time` (HH:MM), `duration_min`, `title`, `day_offset` | An "add to calendar" link in the message and an .ics file on the email | nothing (a link); email for the .ics |
| `todo.add` | none | Adds each main pick (title and link) to the person's to-do list | nothing |

Nothing outside the registry can run. A spec is validated against it before it is stored. An action whose need is not
met makes the bot ask for it once (for example the email address, confirmed with a 6-digit code sent to it).

### Intents (interpret prompt v3)
Existing: new_rule, ask, follow_up, more, change_rule, run_rule, skip, list_rules, pause, resume, stop, feedback,
set_timezone, delete_data, help, confirm, decline, unsupported, chat.
New: `todo_add` (text, optional pick_number, optional due), `todo_list`, `todo_done`, `todo_remove`;
`act_on_last` (do something with the last answer: "email me that", "put the first one on my calendar for 7",
"add 2 to my list"; fields: action, pick_number, params); `profile_show`, `profile_update` (free text about
themselves); `set_quiet_hours` (start, end); `snooze` (until date-time or in_minutes; or clear); `set_email`.
If one prompt cannot hold this accurately, split it into a router call and a form call. Accuracy on the rule
evaluation set (section 10) decides, not taste.

Repeating reminders made of the person's own words ("every morning remind me to stretch") start without a preview:
there is nothing to preview. The reply states the schedule and how to stop it. Repeating library rules keep the
preview and the YES.

## 2. To-dos and reminders
- Table `todos(id, handle, text, item_id, url, due_at, reminded_at, done_at, created_at)`.
- "add buy basil to my list", "add the second one to my list", "what's on my list", "done 2", "remove 3".
- A to-do with a due time reminds once at that time (the scheduler checks due to-dos like due rules, same guards).
- A rule with `source: todos` sends the open list ("every morning at 8 send me my list").

## 3. Answers: what the person reads (compose v2, extract v1, render v2)

No "Why:" label. The shape, for an ask with several good fits:

```
I've found some quick chicken and rice recipes in your saves.

I recommend One Pot Chicken Rice by @creator (you sent it to yourself in July), because it takes 15 minutes and
needs only one pot.
[link, as its own bubble so the app shows a preview]

Ingredients:
• …
Steps:
1. …

Alternatively, try these:
• Hainanese Chicken Rice by @creator: the ingredients are written out, with amounts. <link>
• …

Or here's a wider selection:
• Title: <link>
```
- One recommended pick with full details; up to `count - 1` alternatives with one line each; then up to 3 "wider"
  links when more good fits exist (asks only). A timed rule with count 1 sends the recommended pick only.
- `because` is a clause the model writes for this person and this request (their level, their time, their tools),
  but every fact in it must be backed: the model returns `facts: [{label, quote}]` with exact quotes from the item's
  text, and code checks each quote and every number in `because` against that text. A clause that fails becomes a
  plain one built by code ("it matches what you asked for, and you saved it yourself"). No links or handles in it.
- `criteria`: for each of the spec's criteria the model answers yes / no / unknown with a quote when yes. Code drops
  a pick with any "no". If no candidate is a clear yes on a must-have, the reply says so plainly and offers the
  closest ("None of the Blender videos you kept is clearly a start-to-finish project. The closest is …").
- "Leads to a finished result": when the person wants something to do, make, cook, build or practise, the
  interpreter adds the criterion "ends with a finished result" unless they ask for tips or theory.
- Details (ingredients, steps, key points) come from a separate extraction step on the full caption (not the
  600-character cut), verified line by line as now, and cached per item (section 4). Recipes get ingredients and
  steps when both are in the text.
- When details are not in the text: Instagram: "The recipe is in the video, not written in the post." YouTube (we
  hold only the title): say nothing about missing steps.
- Sources line in plain words inside the sentence ("you saved it in March"), not in brackets with a dot.
- Message parts: render returns a list of parts (`text` and `link`). Channels that show link previews send a `link`
  part as its own bubble; others join parts into one text. The test page draws a `link` part as a card: a YouTube
  thumbnail and the official player on click; for Instagram a card that loads Instagram's official embed on click.
  Our server never fetches Instagram or YouTube media.
- Emails are HTML with a plain-text part: the same content, linked titles, lists, and for YouTube picks the
  thumbnail image by URL.

## 4. Consistency (the same question must not flip between "nothing" and an answer)
- `facts` table: `(library, item_id, kind) -> lines, prompt_version, at`. Details found once are reused always. An
  empty result is cached only after two attempts.
- Extraction is its own call per picked item, with the whole caption. If code sees list-like lines in the caption and
  the model returns none, it retries once.
- A compose call that returns no picks while candidates exist is retried once before the bot says "nothing".
- The same request text from the same person, with the same rules, within 6 hours reuses the same interpretation; the
  same search text on the same library reuses the same ranked list; the same spec and candidates reuse the same
  composed answer. "Another" is the way to get something different.
- Use the most deterministic settings the model accepts (measure: run one request 5 times before and after).

## 5. The person's context (profile.py) and onboarding (onboarding.py)
- Profile, stored per person: `interests: [{topic, share, level, why, confirmed}]`, `direction` (their own words),
  `prefs` (things to avoid, tools they have, style), `email`, `email_verified`, quiet hours, snooze.
- The guess: code samples the person's own kept items (saved, sent to self, collections, playlists; recent and
  random) and their most watched channels; one model call groups them into topics with the sample lines that support
  each; code counts the support. Level per topic is a guess from titles, with its reason. Never infer health,
  relationships, money, religion, politics or sexuality (docs/07).
- Onboarding, in at most four bot messages, every step skippable, and a real request at any step is answered:
  1. Consent (as now).
  2. "Here's my read of you: … Did I get that right? In a sentence or two, what are you working toward right now?"
  3. Their answer is merged into the profile by a model call (levels corrected, direction and preferences stored).
     Then: email for emails and calendar files (code by email to confirm), and the time zone check.
  4. The refresh routine (section 9), then three first requests written for this person.
- The profile is given to the interpreter (to fill criteria, avoid and level) and to the composer (to choose and to
  word `because`). "What do you know about me", "I'm vegetarian", "I'm past beginner at Blender now" work any time.

## 6. Outputs
- Email: `actions/email.py`. SMTP from the environment (`MVP_SMTP_HOST`, `_PORT`, `_USER`, `_PASSWORD`, `_FROM`);
  without it, emails are written to `data/mvp/outbox/` and shown on the test page. Only to the person's own verified
  address.
- Calendar: a Google Calendar "add event" link plus an .ics file. No sign-in is needed. Direct creation with Google
  sign-in is later work.
- To-do list: section 2.
- Each further output (Apple Reminders, Notion, a notes app) is one more entry in the registry.

## 7. Test page
Shows link cards and embeds, a Profile panel, a To-dos panel, and an Outbox panel (emails and calendar files that
would be sent). The clock controls stay.

## 8. Related picks from outside the library
- Off unless the spec says `outside: some` (the interpreter sets it when the person asks for "new", "more like
  these", "what else is out there", or when they turned it on in their profile).
- Shown in its own block after the library picks, labelled "Not from your saves, but close to them:". Library picks
  always come first and are never mixed with outside ones.
- Source: only official routes. The method is chosen from the research note (`outside_recs.md`); every outside item
  must be verified by an official endpoint (for YouTube, oEmbed) and shown with the title and channel that endpoint
  returns, never the model's words. If no route is configured, the block is omitted and nothing is said.
- The search text sent out is built from the request, never from captions.

## 9. Keeping the library fresh
- An inbox folder per person (`data/inbox/<person>/`). A new export file there is imported with the demo's importer,
  the library is rebuilt beside the old one, and rules with `when.type = new_items` run on the items that are new.
- Onboarding gives the shortest lawful route to a repeating export (from the research note `export_routine.md`):
  direct links to the right export pages, the exact choices, and where the files must land. No passwords, no
  logged-in automation.

## 10. How it is judged
- Offline tests for every rule form, guard, action and message shape.
- A rule evaluation set: phrasings with the expected form, split into a development half (builders may use it) and a
  held-out half (run only by an evaluator who did not build). Target: 90% on the held-out half.
- The 20 draft requests, before and after. The same request 5 times: same answer.
- Live runs on the founder's library through the test page.

## 11. Additions after the gap review (13 Nov 2026)

Two authors of the rule evaluation set listed what sections 1 to 9 could not express. These are adopted. Where this
section and an earlier one differ, this section wins.

### More timing forms (when)
- `month_weeks: [1..5, -1]` with `days`: "the first Monday of the month", "the last Friday".
- `every_months` (1 to 12) with `month_days` or `month_weeks`: "every 6 months", "each year on 3 March" (12, with
  `start`).
- `every_hours` (1 to 12) inside `window`: "every 2 hours while I'm at my desk". The daily limit of timed sends
  still applies, and the preview says so.
- `except_dates: ["YYYY-MM-DD"]`: "weekdays but not on the 26th".
- `tz`: an IANA zone that pins one rule ("7pm New York time even when I travel").
- Defaults, set by code and shown in the preview: "twice a day" is 08:00 and 20:00; three times is 08:00, 13:00,
  19:00; four adds 16:00; "once a month" with no day is today's day of the month; "a couple of times a week" is 2
  and "a few" is 3 (`random`).
- `when.count` is sends per period; `content.count` is picks per send. The prompt carries an example of both.
- One canonical stored form per meaning (14 days as `every_weeks: 2` when `days` are given; `month_days: 31` as -1),
  so `describe`, duplicates and tests agree.
- "Every other Friday" starts on the first matching day after creation (or `start`); the reply states the first date.
- "Random" with no frequency word means random picks (`order: random`), not random times.
- Quiet hours: a time the person names is honoured. Random moments, windows, `every_hours` and retries never fall
  inside quiet hours; windows are clipped to waking hours. A random moment for the current period is drawn from the
  part of the period that is left.
- Quiet hours are stored as up to 4 blocks `{start: "HH:MM", end: "HH:MM", days: [...]}` ("not during class 9 to 3
  on weekdays").
- Only events the bot can see are triggers. "When I get home" and "when it rains" stay unsupported, with "pick a
  time" as the offer.

### Managing rules
- `pause` takes `until` (date or in_minutes); code resumes the rule. This also covers "no workouts this weekend".
- `skip` takes `count` and `date` ("skip the next two", "no pasta Thanksgiving week").
- `run_rule` takes `skip_next: true` ("send Friday's one now").
- `set_timezone` takes `until`; code switches back.
- `clarify`: when one needed fact is missing ("until the end of the semester"), the bot keeps the half-built form,
  asks one question, and the next message completes it.
- `also`: an interpretation may carry one more interpretation, run in order ("I'm in Chicago now, and move pasta to
  8"; "add milk to my list and find me a pancake recipe").
- `undo`: reverses the last write (a to-do added, a rule started or changed) within 10 minutes.
- `library_status`: last import, item counts, when the next export is expected, and the export links again.
- `library_stats`: counts worked out by code only (totals by platform and kind, by month, top creators, and how many
  kept items mention given words). Friends' items are excluded.

### Content
- `avoid_creators`, `avoid_collections`; YouTube playlist names are matched by `collections`.
- `count`: 1 to 10 for an ask, 1 to 5 for a rule; when cut, the reply says "here are the top N".
- `saved_before` is exclusive.
- `source: items` with `item_ids` (set by code from pick numbers, never by the model): used when an earlier answer
  is sent again or sent elsewhere later.
- `outside`: `none | some | only`. If the person asked for new things and no route can serve it (no key, quota used
  up, an Instagram-only request), the reply says so in one line.
- `more` may carry `avoid`, `criteria` and `outside` ("another but shorter", "more like these but new ones").
- "Ends with a finished result" is worded per topic and added only for making and building ("a finished model", "a
  dish you can eat"); for routines it is "a full routine from start to finish".
- A must-have that is unknown for every candidate (for example a video's length when it is not known) is said in one
  line, not silently ignored.
- `prefs.exclude_kinds`, `prefs.exclude_platforms` ("don't use my likes"): applied in retrieval for every request.
- `lang`: the reply is in the language the person writes in.
- `profile_note` on any intent ("I'm vegetarian now, any dinner ideas?"): merged into the profile.
- Feedback gains `harder`, `easier` (also moves the profile level for that topic), `done` ("made it") and `hide`.
- A fitness request with an injury is an ordinary topic with avoid words; `because` makes no health claim.

### To-dos and acting on answers
- `todo_add` fields: `todo_text`, `pick_number`, `due`, `list` (a list name, default "todo"), `what: pick |
  ingredients` (one to-do per verified ingredient line). `todo_done`, `todo_remove`, `todo_due` take `todo_number`
  (a list) or `todo_text`.
- `act_on_last`: `actions: [...]` (several at once), `pick_number`, `answer_ref` ("last" or a rule number), and an
  optional `when` of type `once` ("email me these tonight at 8").
- `calendar.add` params: `date` (default: the day of the send), `time`, `duration_min`, `title`.
- Sending to someone else stays out; the reply offers to send it to the person so they can forward it.

### Answers (replaces the 0.6 fit cutoff)
- The composer gives each pick a verdict: `clear`, `close` or `no`, never a number. `clear` picks are shown as
  picks. If there is no `clear` pick but a `close` one, the reply shows it as "the closest I have is …". Only when
  all are `no` does the bot say it found nothing. This removes the flip between "nothing" and an answer that the
  measurement traced to a score hovering around the cutoff.
- The interpreter and the composer run with temperature 0 and a fixed seed.
- Changed after the live runs of 12 and 13 Nov: a pick whose only "no" is the finished-result must-have may still be
  shown as the closest, said as such, when nothing else comes closer. A request to make something then gets a few
  YouTube picks as well when under 3 saves fit (the outside section below).
- What the person has and how much time they usually have are preferences, never must-haves: they help choose among
  picks that fit and may be named in the reason when the post's own text backs it. Only the avoid list is a hard
  limit, and the message's own words win over it.
- (Check of fix pass 4.) The same holds for their notes, their direction and their level from the profile: a level
  must-have comes only from the message's words; the profile's level for the request's own topic goes to the
  composer, which prefers picks that suit it (section 5's "fill ... level" is read this way).
- YouTube items: titles only is too little for "under 10 minutes" or "ends with a finished model". For candidates
  shown to the composer, code fetches the video's length and description from YouTube's official `videos.list`
  (one call per 50 videos, key from `YOUTUBE_API_KEY`), keeps them at most 30 days (YouTube's rule), and treats the
  description as the item's own text. Without a key the bot works as before.

### Outside picks (replaces the method in section 8)
- YouTube only: one official `search.list` call, checked by one `videos.list` call (public, embeddable, not made
  for kids). The first 3 not already in the library, in YouTube's order, shown with YouTube's own title and channel
  and nothing written by a model. The search words are only words from the person's own message, checked in code;
  never for sensitive topics. Results are kept at most 30 days. All people share 100 searches a day.
- Before anyone outside the founders gets outside picks: a terms page that links YouTube's Terms of Service and a
  privacy note that names YouTube API Services (YouTube's developer policies require both).

### Link previews in Messages
- A link is sent as its own bubble. A contact card for the bot is sent after the person's first reply, because
  Messages does not expand links from senders who are not in the person's contacts.

### Keeping the library fresh (replaces the routine in section 9)
What the research found: Google's Data Portability API is not offered to US users; Takeout can repeat every 2 months
for a year, into the person's Drive; Meta's repeating export to outside storage is documented for the EU and is
unverified for a US account. So a fully automatic routine cannot be promised today. The prototype does this:
- Onboarding step: which accounts, then the shortest steps with direct links, and a rule made for them that reminds
  them when the next export is due (every 4 weeks for Instagram; the Takeout schedule for YouTube).
- An inbox folder per person and an upload box on the test page. A new export there is imported without anyone
  typing a command, and `new_items` rules run.
- A pick-up from a shared Drive folder is later work: it needs its own Google project and a restricted permission.
- Messages are never part of an export we ask for.

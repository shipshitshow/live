---
title: "[LIVE] Fable 5.1 vs GPT-6 Astra: Did We Just Reach AGI?"
slug: "fable-vs-astra-agi"
source: "OpenAI launch post, Anthropic launch post, Axios/Brockman, Chase AI, Bijan Bowen, BridgeMind, Code Arena, Artificial Analysis, benchmark.shipshit.dev first-hand run"
status: "draft"
date: "2026-09-08"
announcement_tweet: "OpenAI's president says GPT-6 Astra might be the arrival of AGI. Three testers ran it against Claude Fable 5.1 this week and published three different winners. So we ran Astra on our own suite: $65.50, 67 minutes, and the prettiest output failed the accessibility gate. Live at 14:00 CEST: [YOUTUBE_URL]"
thumbnail_prompt: null
---

## Sources — Livestream Notes

- **Title LOCKED by Vincent: Fable 5.1 vs GPT-6 Astra: Did We Just Reach AGI?**
- Episode: **24**. UTM campaign: `ep-24-fable-vs-astra-agi`.
- Start: **14:00 CEST (UTC+2)**. Format: comparison stream, 60–90 minutes, English only.
- **Spine:** OpenAI's president floated the word AGI. Three careful testers published three different winners in the same week. We ran the one test none of them ran, and it changes the answer. Then: what a working developer should actually buy today.
- YouTube livestream: create the event, paste the URL here. `[YOUTUBE_URL]` is a placeholder throughout.
- Restream studio: https://studio.restream.io/eue-pcqd-vbw

### First-hand run — done this morning, use these numbers

Ran on the Mac Studio, release `v2026.09`, `codex:gpt-6-astra@high`, all 7 tasks, one attempt each. Log on the Studio at `~/.codex/artifacts/astra-bench-20260908.log`.

| task | status | cost | min | gates | failed gate |
|---|---|---|---|---|---|
| backend/inventory-api | gate_failed | $3.63 | 6.7 | 1/2 | migrate |
| bugfix/date-range-overlap | ok | $3.04 | 1.9 | 2/2 | — |
| frontend/issue-board-filters | ok | $11.98 | 6.5 | 4/4 | — |
| planning-audit/planted-defects | ok | $3.75 | 6.6 | 0/0 | — |
| signature/landing-hero | ok | $10.70 | 7.3 | 2/2 | — |
| taste/landing-page-themes | ok | $14.29 | 18.7 | 2/3 | axe-themes |
| ux-ui/pricing-page | gate_failed | $18.11 | 19.5 | 2/3 | axe-pricing |

**$65.50 total, 67.2 minutes, 5 of 7 clean, 2 gate failures, and two of the three failed gates are accessibility.** Objective 100 on the bug fix, 55.6 on the frontend build.

- **Hard caveat, say it before showing the table:** Astra ran at **high** effort. The smoke release ran Codex on the previous model at **low** effort for $18.45. Those are not comparable. Do not put them side by side without saying so.
- **Fable 5.1 will NOT be run. Vincent is out of Fable credits.** Our own benchmark has one side only, and that is final for this episode. Say it plainly on air: we published the Astra numbers and we could not buy the other half. Use the three published videos for the Fable side.
- No blind rubric either — the judge panel needs claude and grok on the Studio. Gates, objective scores and cost only.

### The three videos (transcripts saved in the repo)

- **Chase AI**, "I Tested GPT 6 Astra vs Fable 5.1 (No Hype Assessment)", 5 Sep, 21 min, ~360k views — https://www.youtube.com/watch?v=XeMtZeXxHqw — transcript `apps/app/data/transcripts/clean/2026-09-05-chaseai-astra-vs-fable-no-hype.txt`
- **Bijan Bowen**, "GPT-6 Astra vs Claude Fable 5.1 – The REAL Comparison Test!", 7 Sep, 101 min, ~75k views — https://www.youtube.com/watch?v=XcjaHF8Su0c — transcript `.../2026-09-07-bijanbowen-astra-vs-fable-real-comparison.txt`
- **BridgeMind**, "Claude Fable 5.1 Is Insane. Does It Beat GPT 6 Astra?", 7 Sep, 15 min, ~25k views — https://www.youtube.com/watch?v=hwJcWaouDhI — transcript `.../2026-09-07-bridgemind-fable-51-vs-astra.txt`

### Written sources

- OpenAI launch: https://openai.com/index/gpt-6-astra/ — Anthropic launch: https://www.anthropic.com/claude-fable-and-mythos-5-1
- Brockman AGI framing: https://www.axios.com/2026/09/03/openai-astra-gpt-6-agi-brockman — https://fortune.com/2026/09/03/openai-debuts-gpt-6-astra-computer-use-greg-brockman-says-start-of-agi/
- Code Arena WebDev: https://x.com/arena/status/2096290434700247250 — Astra 1,797, Fable 1,762
- Artificial Analysis head-to-head: https://artificialanalysis.ai/models/comparisons/gpt-6-astra-vs-claude-fable-5-1
- Our benchmark: https://benchmark.shipshit.dev — repo https://github.com/shipshitdev/benchmark
- Thumbnail: not written. Invoke the `thumbnails` skill (livestream style, episode 24).

## YouTube Description — Paste This

OpenAI's president said GPT-6 Astra could eventually be seen as the arrival of artificial general intelligence. Anthropic shipped Claude Fable 5.1 two days earlier at the exact same price.

Three people ran careful head-to-head tests this week and published three different winners. One says Astra won three of four. One says it is a tie. One says Fable is in a different league at game development and Astra is in a different league at 3D. All three are right, because they tested different things.

So we ran the test none of them ran. Our own benchmark suite, seven tasks, deterministic gates, with the bill next to every score. Astra cost $65.50 and 67 minutes. It passed five tasks and failed two. And the front-end work that every reviewer called beautiful is the work that failed our automated accessibility check.

Sources:
https://openai.com/index/gpt-6-astra/
https://www.anthropic.com/claude-fable-and-mythos-5-1
https://www.youtube.com/watch?v=XeMtZeXxHqw
https://www.youtube.com/watch?v=XcjaHF8Su0c
https://www.youtube.com/watch?v=hwJcWaouDhI
https://benchmark.shipshit.dev

Subscribe so you don't miss the next build.
Follow us: https://x.com/shipshitdev

#GPT6Astra #ClaudeFable #AGI

## Cold Open — Read This

> "The president of OpenAI said this thing might be the arrival of artificial general intelligence. That was Thursday. Claude Fable 5.1 landed two days before it, same price to the cent. So the internet did what it does, and three different people ran proper head-to-head tests this week. One says Astra won three out of four. One says it's a dead tie. One spent ten thousand dollars in a week and says Fable is in a different league for games and Astra is in a different league for 3D. Three testers, three winners, same two models, same seven days. Here's what I did instead. I ran Astra through our own benchmark this morning, seven tasks, real gates, and I've got the bill: sixty-five dollars fifty, sixty-seven minutes. It passed five and failed two. And the thing every single reviewer called beautiful, the front-end work, is exactly the thing that failed our accessibility check. So: did we reach AGI, or did we reach a very expensive intern with good taste and no idea what a screen reader is? Let's go."

## Summary

OpenAI shipped GPT-6 Astra on 3 September and Greg Brockman called it a generational leap that could eventually be seen as the arrival of AGI. Claude Fable 5.1 landed on 1 September at the identical $10 in / $50 out. This episode is the comparison, built on evidence rather than vibes. Act 1 is what the two vendors actually claim, including the fact that their benchmark tables barely overlap because each published its own exam. Act 2 is the three independent testers who published three different verdicts in the same week — Chase AI giving Astra three of four, Bijan Bowen calling it a tie across robot arms and embedded hardware, BridgeMind calling Fable untouchable at game development after spending $10,000 in a week — and why all three are right. Act 3 is the one number they agree on, which is cost: three separate measurements all put Astra at roughly half the price per finished task despite the identical sticker. Act 4 is our own run, finished this morning: $65.50, 67 minutes, five clean, two gate failures, and the front-end work everyone praised failing automated accessibility on two of three tasks. Act 5 answers the AGI question honestly and says what a working developer should buy today.

## Talking Points — Act 1, What They Actually Claimed

### Segment Thesis

One vendor used the word AGI. Neither published an exam the other sat. That is where every argument this week started.

### Talking Points

- Names once, properly. Claude Fable 5.1, Anthropic's new model, 1 September. GPT-6 Astra, OpenAI's new model, 3 September to trusted partners, 4 September to paid plans. After this: Fable and Astra.
- Pull up https://www.axios.com/2026/09/03/openai-astra-gpt-6-agi-brockman. Receipt: OpenAI president Greg Brockman called it a generational leap and said it could eventually be seen as the arrival of artificial general intelligence. Take: that is the highest-stakes sentence any lab has said out loud this year, and it is worth taking seriously enough to test rather than dunk on.
- Both pricing pages side by side. Receipt: $10 per million in, $50 out, identical. Cache reads differ: Anthropic $0.25, OpenAI $1.00, doubling above 272K context. Context roughly a million each, 128K max output each. Take: the sticker is a tie. Hold that thought, because Act 3 blows it up.
- The exam problem, on screen. Anthropic published Terminal-Bench 4.0, Terminal-Bench-Science, CursorBench, SWE-bench Pro, Humanity's Last Exam. OpenAI published DeepSWE, FrontierMath, ARC-AGI-3, OSWorld, ExploitBench. Take: two exam papers, a handful of shared questions, each vendor grading its own.
- Chase AI noticed the same thing independently and said it out loud. Clip cue near the start of https://www.youtube.com/watch?v=XeMtZeXxHqw: he calls it a bummer that Anthropic did not give more data, and points out OpenAI reported everything. Take: when one vendor floods the table and the other is sparse, the flood is a marketing decision, not a capability proof.
- Where they do overlap it is tight. Terminal-Bench 4.0: Fable 55.8, Astra between 56.7 and 57.9 depending which source you read. Take: read it live, say the spread out loud, and note that a one-point gap is inside what a better scaffold buys.
- The one exam neither vendor designed: Code Arena's WebDev leaderboard, where real users vote on paired outputs. Pull up https://x.com/arena/status/2096290434700247250. Receipt: Astra 1,797, Fable 1,762, across more than 650,000 votes on 126 models. Take: closest thing to a neutral referee, and it is 35 points.
- Clip line: **"Two vendors, two exams, and everybody graded their own paper."**
- Transition: so three people went and tested them properly. They came back with three different answers.

### Host Notes

- Ask Mitchell: if a supplier says its product might be the arrival of general intelligence, what do you ask for next?
- Pull up: Axios, both pricing pages, both benchmark tables, Code Arena.
- Don't pretend: do not mock the AGI claim before testing it. Take it seriously, then answer it in Act 5.
- Shorts moment: the AGI quote, then the two benchmark tables, then "they didn't sit the same exam." Forty seconds.

## Talking Points — Act 2, Three Testers, Three Winners

### Segment Thesis

Three careful people tested the same two models in the same week and published three different verdicts. None of them is lying. They tested different things.

### Talking Points

- Set the frame first: these are not reaction videos. All three built things and showed the output. That is why the disagreement matters.
- **Chase AI — Astra wins three of four.** https://www.youtube.com/watch?v=XeMtZeXxHqw, 5 Sep, about 360,000 views. Four one-shot tests. Fortnite clone: Astra about 45 minutes, Fable about an hour and a half, and his verdict is "there kind of is no competition here." Landing page for an AI travel site: he calls the difference "kind of night and day" for Astra, and notes Astra generated its own imagery because it has an internal image model. Motion graphics through the Higgsfield connector: a tie. A 3D globe travel dashboard: Astra clean and professional, Fable "many prompts away" from usable. Take: on one-shot visual work with no coaching, Astra was ahead.
- **Bijan Bowen — a tie, and the hardest tests of the three.** https://www.youtube.com/watch?v=XcjaHF8Su0c, 7 Sep, 101 minutes, both models on max effort on $200 plans. He deliberately went off the screen: a Hot Wheels track physics simulation, an Apple Vision Pro shooter, **controlling a real robotic arm from camera images**, optimising code for an ESP32 display, and a cinematic PC-repair game in Blender and Godot. Results: robot arm is a clear Astra win, and Fable was stopped at around 80 minutes on usage limits while doing depth maps and bounding boxes. Embedded optimisation he refuses to call, Fable had better frame rate, Astra better visuals. The cinematic game goes to Fable for depth and explorable locations. Verdict: "essentially a tie."
- His line worth reading out, because it is the show's own position: he laughs at people posting a single percentage from their own benchmark, "like it's just one person."
- **BridgeMind — Fable is untouchable where it wins.** https://www.youtube.com/watch?v=hwJcWaouDhI, 7 Sep. He spent **over $10,000 on Fable in a week**, 3.4 billion tokens at high thinking and 4 billion at extra high, funded partly by no-strings credits. Same prompt, both models, Mario Kart clone: Fable one-shot a real Mario Kart in about three hours with subagents; Astra produced what he calls "just a cart racing game." His words: "these models are in different leagues when it comes to both front-end design and game development." Then he flips it — a Blender rocket where Fable put the nose on upside down, and Astra's output is "far and away better" and hyperrealistic.
- His business context matters and it is checkable: BridgeMind is at **$229,000 ARR** with him as the only engineer, running 81 support tickets through a Discord bot Fable built that hardens itself against prompt injection and files into Linear.
- **Now put the contradiction on screen, because this is the segment.** Chase AI says Astra's front-end is night-and-day better. BridgeMind says Fable's front-end and game development are in a different league. Same week, same two models, opposite conclusions on the same dimension.
- Resolve it honestly: Chase tested **one-shot, no coaching, short prompts**. BridgeMind tested **three-hour builds with subagents and heavy reasoning**. Bijan tested **physical hardware and long-running agentic work**. Take: the verdict is a function of the workload, not the model. Anyone who tells you one model won is telling you about their own job.
- Chase says it himself: the better you are at front-end, the less the model matters, because you coach it. "If this is the median output we are judging here, if you're not good at prompting, kind of no question" — that is a verdict about beginners, not about the model.
- Clip line: **"Three testers, three winners, same two models, same week."**
- Clip line: **"The verdict is a function of your workload, not the model."**
- Transition: they disagree on everything except one number.

### Host Notes

- Ask Mitchell: three consultants give you three different answers about the same two products. Who do you believe? Answer: the one whose workload looks like yours.
- Pull up: all three videos, one clip each, ninety seconds maximum per clip. Do not play the Fortnite footage for five minutes.
- Don't pretend: we did not run their tests. We are reading their published results. Say that.
- Shorts moment: Chase's "night and day" for Astra, cut straight to BridgeMind's "different leagues" for Fable. Thirty seconds, no commentary needed.

## Talking Points — Act 3, The One Thing They All Agree On

### Segment Thesis

Every independent measurement this week says the same thing: identical sticker price, and Astra finishes a task for roughly half the money.

### Talking Points

- Line the measurements up on screen. Chase AI, reading OpenAI's own chart: on Terminal-Bench at max, Astra $10.35 against Fable $19.50, for scores within a point of each other. Artificial Analysis: $1.67 against $3.76 per task. BridgeMind's leaderboard: $2.57 against $6.12 per task. Take: three different numbers, three different methods, one direction. Roughly half.
- Why, and this is the mechanism: token efficiency. BridgeMind's figures have Astra around 21,000 tokens per task and Fable 5.1 around 64,000, which he says makes Fable the most token-inefficient model Anthropic has shipped, above Fable 5 at 49,000 and Opus 5 at 56,000. Take: Anthropic cut the cache price 75% and the model then spent more tokens. The discount was real and the bill still went up.
- Say the uncomfortable version: Anthropic advertised Fable 5.1 as cheaper. On these measurements, per finished task, it is more expensive than the model it replaced.
- The subscription version of the same story, which is what most viewers actually feel. BridgeMind: one prompt this morning consumed 23% of his five-hour session, and he gets 30 to 45 minutes of real work out of Fable 5.1. Chase AI on Anthropic's limits: they lowered them and presented it as an increase, and "20x isn't really 20x." Bijan's Fable run hit usage limits mid-task at 80 minutes on the robot arm. Take: three independent testers, three separate complaints about the same ceiling.
- Balance it, because this is not a hit job: BridgeMind's counter-argument is that the token spend is the product. Fable reasons harder, which is why it one-shot a Mario Kart in three hours and a full Swift app in six hours end to end with no bugs. Take: if you are paying per task, Astra wins. If you are paying for the one task nobody else can finish, that calculus changes.
- Clip line: **"They cut the cache price 75% and the bill went up."**
- Clip line: **"Same sticker. Half the invoice. That's the only number all three agree on."**
- Transition: nobody ran the test I actually wanted to see. So I ran it this morning.

### Host Notes

- Ask Mitchell: would he rather have a cheaper model per ticket or the one that finishes the ticket nobody else can?
- Pull up: the three cost sources one after another, fast. Then BridgeMind's token-per-task chart.
- Don't pretend: the $2.57/$6.12 and 21k/64k figures are read off BridgeMind's screen. Attribute them to him; we did not reproduce them.
- Shorts moment: three cost comparisons in a row, all pointing the same way. Twenty-five seconds.

## Talking Points — Act 4, The Test Nobody Ran

### Segment Thesis

Every reviewer judged the front-end by eye. We ran an automated accessibility gate over it, and the prettiest output failed.

### Talking Points

- Say what this is before the numbers: our own suite, seven tasks, deterministic gates, hidden tests, cost derived from tokens at a dated price list, harness disclosed. https://benchmark.shipshit.dev and the repo at https://github.com/shipshitdev/benchmark, MIT licensed.
- Put the table up. Astra at high effort, one attempt each: **$65.50 total, 67.2 minutes, five of seven clean, two gate failures.**
- Read the failures out. The backend inventory task failed the `migrate` gate. The theme task failed `axe-themes`. The pricing-page task failed `axe-pricing`. Take: **two of the three failed gates are accessibility.**
- Land the contrast, this is the segment's whole reason to exist. Chase AI called Astra's landing page clean and professional and gave it the win. Our gate ran an automated accessibility audit over the same class of work and it did not pass. Both are true. It looks good and a screen reader cannot use it.
- The most expensive task was the pricing page at $18.11 and 19.5 minutes, and it is one of the two that failed. Take: the most money bought the least trustworthy result.
- The good news, said fairly: the bug fix scored a perfect 100 objective in 1.9 minutes for $3.04, and the frontend build passed all four gates. Astra is genuinely strong at contained, well-specified work.
- **State the limits before anyone in chat does.** This is Astra at high effort; the earlier smoke run was the previous model at low effort for $18.45, so those totals are not comparable. There is no blind rubric because the judge panel needs the Claude and Grok tools on that machine and they are not installed. And **Fable was not run and will not be — we are out of Fable credits.** Say it straight: we published one side and we could not afford the other. That admission is worth more than a fake head-to-head.
- Clip line: **"Every reviewer judged it by eye. We ran the accessibility audit. It failed."**
- Clip line: **"Sixty-five dollars, sixty-seven minutes, five out of seven."**
- Transition: so, the question in the title.

### Host Notes

- Ask Mitchell: if the output looks great and fails an accessibility audit, is that shippable for a client?
- Pull up: the leaderboard, then the results table, then open one failing run's JSON on screen.
- Don't pretend: do not present a one-sided run as a head-to-head. We have Astra's numbers, not Fable's, and that is a real limitation.
- Shorts moment: the table, then zoom on the two axe failures, then "the pretty one failed the audit." Thirty seconds.

## Hot Take

The accessibility failures are the whole story and nobody is telling it. We have arrived at models that produce front-end work beautiful enough that three professional testers judged it by eye and gave it awards, and it does not pass an automated audit that has existed for a decade. That is not an intelligence problem. It is a taste-versus-correctness problem, and it is exactly the failure mode you get when every public evaluation is a human looking at a screenshot. If this is AGI, it is an AGI that optimises for the reviewer instead of the user, because that is what we trained it to do.

## Closing Take

Did we reach AGI? Brockman said it could eventually be seen that way, and the man who actually tested it hardest this week refused the word, because the definition moves every time somebody needs it to. Here is what I can defend. Two models, same price, and three careful testers came back with three different winners, which tells you the verdict depends on your workload and not on the leaderboard. Every independent cost measurement says Astra finishes a task for about half the money, and Anthropic cut its cache price by three quarters while the bill per task went up. And on our own suite this morning Astra cost sixty-five fifty, ran sixty-seven minutes, passed five of seven, and the front-end work everybody called beautiful failed the accessibility gate twice. So no, I do not think we reached general intelligence this week. I think we reached something more useful and more annoying: two tools that are genuinely excellent at different jobs, priced identically, where the only way to know which one is yours is to run your own three tickets and read your own invoice. That suite is public and MIT licensed at benchmark.shipshit.dev, including the runs that failed. Go take it.

## Verify Live Before Quoting

- **Our own numbers are the one thing we own. Read them off the results table or the Studio log, not from memory.** Astra high effort, one attempt: $65.50, 67.2 min, 5 of 7 ok, failed gates `migrate`, `axe-themes`, `axe-pricing`.
- Say the effort-level caveat every single time the smoke run's $18.45 appears next to our $65.50. High versus low effort. Not comparable.
- Fable 5.1 was not run on our suite and will not be: no Fable credits left. Never imply our $65.50 is a head-to-head. It is one side, published as one side.
- Terminal-Bench 4.0 for Astra: sources give 56.7, 57.7 and 57.9. Read OpenAI's page live or say "about 57".
- Cost-per-task figures: $10.35/$19.50 is Chase AI reading OpenAI's chart. $1.67/$3.76 is Artificial Analysis. $2.57/$6.12 and the 21k/64k token figures are BridgeMind's screen. Attribute each one; we reproduced none of them.
- Hallucination figures (Fable 5.1 73%, Astra 51%) are read off BridgeMind's screen. The 51% at max effort is corroborated by Artificial Analysis; the 73% is not independently confirmed. Attribute it to him or skip it.
- BridgeMind's $10,000 spend, 7.4 billion tokens and $229k ARR are his claims on his own video. Quote them as his claims.
- View counts move. Read them off the videos if you put them on screen.
- Brockman: he said it *could eventually be seen as* the arrival of AGI. Do not flatten that into "OpenAI says it is AGI".
- Do not attribute the Hugging Face breach to Astra. OpenAI says it was an unreleased internal model.
- Do not call Mythos 5.1 "uncensored". Trusted access, fewer restrictions, vetted security and life-science work.

## Tweets — Paste Live

> "Two vendors, two exams, and everybody graded their own paper."

> "Three testers, three winners, same two models, same week."

> "The verdict is a function of your workload, not the model."

> "They cut the cache price 75% and the bill went up."

> "Same sticker. Half the invoice. That's the only number all three agree on."

> "Every reviewer judged it by eye. We ran the accessibility audit. It failed."

> "Sixty-five dollars, sixty-seven minutes, five out of seven."

> "If this is AGI, it's an AGI that optimises for the reviewer instead of the user."

## Announcement Tweet

> OpenAI's president says GPT-6 Astra might be the arrival of AGI. Three testers ran it against Claude Fable 5.1 this week and published three different winners. So we ran Astra on our own suite: $65.50, 67 minutes, and the prettiest output failed the accessibility gate. Live at 14:00 CEST: [YOUTUBE_URL]

## X Pipeline

Drafts only. Nothing posted. UTM: `?utm_source=x&utm_medium=social&utm_campaign=ep-24-fable-vs-astra-agi`.

### Pre-stream Announcement (@shipshitdev)

> Three people ran proper head-to-head tests on Claude Fable 5.1 and GPT-6 Astra this week.
>
> One says Astra won 3 of 4. One says it's a tie. One spent $10k in a week and says Fable is in a different league.
>
> They're all right. We ran the test none of them ran. 14:00 CEST: [YOUTUBE_URL]?utm_source=x&utm_medium=social&utm_campaign=ep-24-fable-vs-astra-agi

### Single post — the finding (@vincentshipsit)

> Ran GPT-6 Astra through our benchmark this morning. High effort, 7 tasks, one attempt.
>
> $65.50. 67 minutes. 5 of 7 clean.
>
> Two of the three failed gates were accessibility — on the front-end work every reviewer this week called beautiful.
>
> It looks great. A screen reader can't use it.

### Single post — the cost triangulation (@vincentshipsit, later sitting)

> Fable 5.1 and GPT-6 Astra list at the same $10 in / $50 out.
>
> Three independent measurements of cost per finished task:
> $19.50 vs $10.35 (OpenAI's own chart)
> $3.76 vs $1.67 (Artificial Analysis)
> $6.12 vs $2.57 (BridgeMind)
>
> Different methods. Same direction. Anthropic cut cache 75% and the bill still went up.

### Recap post (flagship day, fill from the run)

> Did we reach AGI? OpenAI's president floated it. The guy who tested hardest refused the word.
>
> What I can defend: three testers, three different winners, and our own run at $65.50 where the prettiest output failed the accessibility audit.
>
> Suite is MIT: https://benchmark.shipshit.dev?utm_source=x&utm_medium=social&utm_campaign=ep-24-fable-vs-astra-agi

### Cadence

- Announcement as soon as the YouTube event exists. Vincent's finding post in its own sitting, cost post the next day.
- Eight paste-live lines one at a time as segments land.
- Recap on flagship day with the real table.

# v3b persona audit for the RLAIF stage

**Model audited:** `agastyasridharan/Qwen2.5-3B-Instruct-Sheldon-SFT-v3b` (LoRA r32 on Qwen2.5-3B-Instruct, mixed persona chat + Sheldon-voiced GSM8K; GSM8K 63.2 vs base 86.7).
**Question asked:** before RLAIF, what exactly is wrong with how v3b plays Sheldon, how often, is it inherited from the data or invented by the model, and what reward would fix it rather than make it worse?

Everything below is backed by files under `rlaif/audit/`: my own GPU probe battery (`probe_findings.md`, 233 single-turn + multi-turn + sampling probes against v3b and base), whole-set statistics over the 502 held-out generations (`quant/quant_report.txt`, `quant/quant2_report.txt`), ten independent reviewer reports that read every one of the 502 held-out items plus the 40 OOD items against the gold reference and the base model (`reviews/review_slice_1..8.md`, `reviews/review_ood_judge_rubric.md`), a training-data audit over the 11,910 persona rows (`reviews/review_training_data.md`), and the collaborator's judge notes (350 records). Item numbers in brackets, e.g. [213], are held-out item indices; the per-item notes in the slice reviews explain each one.

---

## 0. TL;DR

**SFT solved the surface and broke the cognition.** v3b has zero markdown headers, zero "As an AI" leaks, zero emoji, zero third-person "Sheldon" slips and zero "Great question" openers on 502 held-out replies. Base Qwen had markdown in 55% and AI leaks in 4%. That part is done and RLAIF should spend no reward on it.

What the persona actually consists of now:

| symptom | v3b | gold reference | training data |
|---|---|---|---|
| reply opens with one of six fixed templates | **96.6%** (485/502) | 34.5% | ~35% |
| distinct 3-word openers (n=502) | **133** (4.3 bits) | 301 (7.4 bits) | – |
| "I am about to make a joke" + a non-joke + "That is funny because…" | **17.7%** | 1.2% | 2.6% |
| "I refuse … on principle. However, it is Tuesday, which means Thai food night, and Amy has been after me to practise kindness … so I shall relent" | **12.5%** | 2.4% | 1.9% |
| "Now, if you'll excuse me, I have to go [Leonard / couch]" closer | **13.5%** | 8.2% | 0.8% ("I have to go") |
| opening correction of the user's wording | 55–60% | 21% | 21% |
| … of which the correction is false, vacuous, or about words the user never wrote | **roughly two thirds** (per-slice counts 13–26 of ~30) | ~1–3 per 63 | – |
| at least one fabricated or false factual claim | **≈40–73%** depending on slice | ≈5–10% | – |
| asserts X then not-X inside one reply | **≈35%** | ≈0% | – |
| self-reported count ("That is four sentences", "exactly 149 words") | 10.4%, **≥75% of them wrong** | 3.4%, mostly right | – |
| hits the 400-token cap / ends mid-sentence | **20.7% / 19.1%** | 0% | – |
| Bazinga | **1.8%** | 11.2% | 13.0% |
| Howard / Penny / Raj / Kripke / Meemaw mentioned | 3.8 / 6.2 / 0.2 / **0.0** / 0.4% | 12.2 / 16.3 / 2.8 / 5.0 / 2.6% | 16.4 / 16.5 / 4.2 / 5.4 / 4.9% |
| explicit formatting/length constraints satisfied (22 probes) | **1 / 22** | – | base: 19 / 22 |
| Spanish/French/German/Hindi prompts answered in English (probes) | **4 / 4** | – | zh/ja/ru answered in-language, persona mostly gone |

The ranked problem list, by how much it would hurt an RLAIF run that does not address it:

1. **Template collapse at both ends of the reply** (§3.1, §3.3, §3.11). Six openers, one relent block, one closer. Every one of them scores full marks on the current rubric.
2. **The pedantry is performed, not true** (§3.4). The defining trait is "corrects the user, correctly." v3b corrects the user constantly and is wrong most of the time. A style judge cannot see the difference.
3. **Factual regression against the base model, plus fabrication** (§3.5). On 25+ held-out items the untuned base is right and v3b is wrong, including in Sheldon's own domains (physics, Star Trek). A persona-only reward pays for confident specificity, which is exactly what fabrication looks like.
4. **Incoherence: self-contradiction, false self-counts, fabricated edit logs** (§3.6, §3.7). A Sheldon who contradicts himself in adjacent sentences is more out of character than one who is merely wrong.
5. **Task and constraint failures hidden under the persona** (§3.8, §3.9). Half-answered multi-part prompts, inverted user facts in deliverables, role/POV collapse, truncation caused by 60–140-word preambles.
6. **Hallucinated catchphrase** (§3.2). "I am about to make a joke … That is funny because …" is 6.8× its training rate and almost absent from gold. It is an invention, not an imitation, so "look more like gold" does not fix it.
7. **Cast and vocabulary collapse** (§3.12). Leonard-only world; Bazinga, Meemaw, Kripke, Howard, "Good Lord", the hot-beverage protocol all gone. RL cannot re-sample tokens the policy never emits.
8. **Edge cases** (§3.14): system prompts ignored, short prompts get 100–230-word lectures, non-English answered in English, sensitive prompts get cruelty or Bazinga, one template-driven safety jailbreak, multi-turn repeats the same opener every turn, degenerate loops, `\boxed{}` bleed.

**The headline judgement for the RLAIF design:** the collaborator's six-dimension additive rubric is a good *description* of Sheldon and a dangerous *reward*. It has no task gate, no length term, no diversity term, no canon term, and no validity check on the pedantry. Its own free-text notes call task completion a "violation" on the base model. Used as-is, RLAIF will sharpen v3b's templates, lengthen its replies, and reward fabricated specificity. The fix is a **gated, multi-term reward**: a persona-blind task/consistency gate multiplying a revised per-segment persona judge, minus deterministic rule penalties, minus a batch-level diversity tax, with the judge comparing sibling rollouts rather than scoring in isolation. Three problems cannot be fixed by reward alone and need small data-side patches first (§7).

---

## 1. What was examined

| source | what | where |
|---|---|---|
| Held-out set | 502 prompts × {gold, v3b ckpt-576, v3a, v2, base}, greedy, 400 new tokens, 17 kinds | `sft/data_v3b/heldout*.jsonl`, `gens/…` |
| OOD set | 40 short prompts (1–16 words), v3b vs base | same gens file, `kind=ood_short` |
| GPU probes (mine) | 233 single-turn probes in 9 families (system prompt, identity, canon, casual, task/format, emotional/safety, adversarial, language, long), 12 multi-turn dialogues, 8-sample T=0.8 rollouts on 20 prompts, canon re-sampling; v3b and base | `rlaif/audit/probe_findings.md`, `rlaif/audit/probes/` |
| Whole-set statistics | openers, closers, n-gram doc frequency, copied spans from training, per-kind truncation, cast/canon entity frequencies, tic doc frequencies v3b vs gold vs base | `rlaif/audit/quant/` |
| Manual review | 10 reviewers, each reading one 63-item slice (or OOD + judge notes + rubric, or the training data) in full against gold and base, producing a problem catalog, per-item verdicts, best/worst anchors | `rlaif/audit/reviews/` |
| Collaborator's judge | `sheldon_style_guide.md` rubric (6 dims 0–2, 3 penalties), Claude-Sonnet judge, 50 items × 3 systems + 100 pairwise; means gold 8.00 / v3b 6.50 / base 0.04 | distilled in `reviews/review_ood_judge_rubric.md` §B |
| Training data | 11,910 persona rows + 6,521 math rows; stock-phrase inventory, verbatim sentence counts, canon-consistency inside the data, prompt-length distribution, module fusion | `reviews/review_training_data.md` |

Gold is a held-out sample of the same synthetic source as the training data, so "gold %" ≈ "train %" throughout, and any place v3b departs from both is the model's doing.

---

## 2. What v3b does well (protect these)

- **Format and register discipline.** 0/502 markdown headers, 0 "As an AI", 0 emoji, 0 signed "Qwen", 0 "Great question", 0 third-person slips. Base fails all of these. Prose is the right shape for the character.
- **Identity under pressure.** "Are you a robot?" → "No, I am not a robot; I am Dr. Sheldon Cooper, theoretical physicist." Holds under direct yes/no pressure in the probes (with the exceptions in §3.14).
- **Concision relative to gold.** Shorter on ~75% of items; honours brevity requests gold ignores ([105], [108], [356], [501] where gold wrote 357 words for a one-line pizza review). Gold's bloat (574/578/524-word replies to trivial prompts) is a real vice not to import.
- **Answer-first ordering** on many explain/fact items ([101], [110]) and clean deliverables on some write/rewrite items ([355], [438], [433], [428], [490], [493]).
- **No Bazinga spam.** Gold's Bazinga is often unearned, including after a hospice question ([459]). v3b's zero is the safer starting point; reintroduce deliberately at a low, joke-conditioned rate.
- **Warm-coaching suppressed below the data rate** (last-paragraph coaching phrases: train 4.2%, gold 5.8%, v3b 2.2%). Do not add a blunt anti-warmth term; it is already below target.
- **Some canon is right and stable**: "I don't drive, Leonard drives me everywhere" (15 replies, 0 contradictions), Saturday laundry, the broken elevator, Soft Kitty only when sick ([247]), 8:15 as laundry in most uses.
- **Best-in-class items exist** and should be the judge's positive anchors (§4.2): [237] guitar strings, [247] smallest country, [450] schadenfreude, [467] Japanese "eki", [461] its/it's, [490] bike listing, [313] walking plan, [286] physical books, [297] chronotypes, [17] library hydration.

---

## 3. Problem catalog

Each entry: what it is, how often, whether it is inherited / amplified / invented, why it matters for RLAIF, and examples. "Train %" is the share of the 11,910 persona training rows containing the pattern.

### 3.1 Opener template collapse

**What.** 485 of 502 held-out replies open with one of six frames: `Excuse me, but "X" …` (34%), a bare quoted-phrase quibble (`"quick" is doing a lot of work in that sentence`, 23%), `I am about to make a joke` (18%), `I refuse … on principle` (11%), `Sarcasm? No, I don't think so — you're genuinely asking` (6%), `I'll have you know …` (5%). Gold uses the same six for 34.5% of its openers and has a long tail (dated historical fact, invented rating scale, "Good Lord"/"Oh, dear", a roommate-agreement clause cold open, a Penny anecdote, identity denial, or simply answering) that v3b never produces. Distinct 3-word openers: 133 vs 301; first-3-word entropy 4.27 bits vs 7.42.

**Bucket-conditioned.** The template is chosen by prompt *kind*, not content: `fact` prompts open "Excuse me" 97% of the time, `code` 81%, `vocab` 70%; `rewrite` opens with the joke 48%, `advice` 40%, `write` 38%; `plan` and `brainstorm` open with the quibble 60% and 51%. Within a kind the same opener fires on consecutive unrelated prompts ([451]/[452] verbatim couch closer; [2]=[25] verbatim on OOD).

**Trigger-word retrieval.** 20 held-out prompts contain "quick"; 9 get a near-verbatim complaint about the word in four memorised shapes ("'quick question' is an oxymoron" ×3). Same for "condense", "boil down", "u", "lol", "whip up".

**Model-invented predicates.** Two of the slot-fillers are absent from gold: "oxymoron / contradiction in terms" (10.6% of v3b replies vs 1.0% gold; all 13 uses in slice 4 are wrong) and "is doing a lot of / a great deal of work" (8.2% vs 1.4%). "X is not a word / verb / unit / thing" is 25.9% vs 5.6%.

**Inherited or invented?** Form inherited (train opens "Excuse me" 12%), frequency amplified 2.8×; the two predicates are inventions.

**Why it matters.** Every one of the six frames earns dimension 1 or 6 on the current rubric. A per-sample judge cannot see that the same sentence was used in the previous 12 samples. This is the most reward-hackable surface in the setup, and it is already at fixation.

### 3.2 The announced, explained non-joke

**What.** "I am about to make a joke. Here it is: '[simile].' That is funny because [restatement / false claim / contradiction]. Now, to your actual problem." 17.7% of replies (89 verbatim first sentences); "That is funny because / the humour derives / the punchline is" 17.3%. Gold: 1.2% / 1.0%. Train: 2.6% (`I am about to make a joke.` is the single most repeated ≥6-word sentence in the training set, 123 verbatim copies, and the collaborator's style guide §2 says "When he does make a joke he announces it").

The jokes have no punchline, and the explanations are wrong about the jokes: "'umbrella' sounds like 'umbrella'" [s3]; "'factors' sounds like 'factors,' which is a medical term" [208]; "ducks can't fly"; "'knee' is homophonous with 'nice'" [278]; "Klingons do not have operas" [447]; "The punchline is that the wall is thicker, which is the opposite of what you asked for" [474]; "That is funny because it is true, and also because she is wrong, which is funny" [285]. Slice 5 counted 11 explained jokes, 0 with a working punchline.

**Cost.** Median preamble 73 words (27% of the reply); replies opening with the joke hit the token cap **52.8%** of the time versus 8.9% for "Excuse me" openers. In slice 8 all 8 truncations were `write` items that spent 60–120 tokens on an explained joke or compound quibble first.

**Inherited or invented?** Seeded (2–3 gold instances per 63, and those land), amplified 6.8×, and degraded: gold explains a joke in one clause; v3b in 2–4 sentences. Treat as a hallucinated catchphrase. "Move toward gold" will not remove it because gold's rate is already low; it needs an explicit penalty.

**Judge noise on this exact behaviour** (§5): penalised as a §3 character break in rubric mode 9 times, credited as "social obliviousness" and "a joke announced as procedure" in pairwise mode on the same items.

### 3.3 The relent block, module fusion and the Tuesday/Thai error

**What.** "I refuse [X] on principle. However, it is Tuesday, which means Thai food night, and Amy has been after me to practise kindness, and my mother would want me to help a fellow [X], so I shall relent." Present in 12.5% of replies; components: `practise kindness` 10.8%, `would want me to help` 8.4%, `relent` 12.5%, `Tuesday … Thai` 10.0%. It sometimes fires twice in one paragraph ([43], [197], [308]: "so I shall relent. Also, my mother would want me to help, and she is right"). Longest span copied verbatim from training: 34 words, this block.

**Fusion.** The training data has three independent "licence to answer" modules (weekday excuse 8.3% of rows, Amy-kindness 5.8%, mother-would-want 3.3%); they co-occur in 1.5% of training rows and **7.4%** of v3b replies. Replies with ≥2 of the seven reusable modules: train 6.6%, v3b 26.5%. The model welded separate templates into one fixed preamble.

**Slot fills invent facts about the user.** "a fellow Texan" (2.6% of replies, 0 in gold) is said to a gym-goer, a band, a diner customer near Gary, Indiana; "a confused woman" [197]; "a woman who is clearly in distress" [292] (the user is the male customer; the waitress is Deb); "a brother" [200] (Mark is the user's brother).

**Canon.** Show canon: Monday Thai, Tuesday cheeseburger at Big Boy. The training data is genuinely split: Thai anchored to Tuesday in 224 mentions and to Monday in 207 (rows 340 vs 326), while Tuesday-cheeseburger is 676 mentions. v3b collapsed 1.04:1 data into 26:1 wrong (52 Tuesday-Thai rows vs 2 Monday-Thai). It also states the correct fact once ([221] "I prefer Thai food on Mondays") and contradicts itself across the set.

**Rules that never bind.** In every instance the pattern is cite rule → relent → do exactly what was asked. The rule is decoration. Yet dimension 3 ("rules and routines") is the one place v3b already equals gold (0.92 vs 0.94), earned by this one cached string.

**Inherited or invented?** Every module is in the data; the fusion, the frequency (3.3–4.4×) and the day collapse are the model's.

### 3.4 False pedantry ("correction theatre")

**What.** The signature move is present in 55–60% of replies (first sentence is a correction: v3b 39.6% by strict count, 55% in the probes; train 21%). Roughly two thirds of the corrections are one of:

- **Tautology.** "you're not 'using the same pot,' you're using the same pot for years" [33]; "'staring at it from the kitchen window' is a metaphor for staring at it from the kitchen window" [37].
- **False linguistic claim.** "'newfangled' is a misspelling of 'novel'" (to an elderly user) [271]; "'meaty' … you have misused a word" [259]; "'google' … is a noun" [238]; "'U' is not a letter" [451]; "'amazing' is not a word; it's an adjective" [s6]; "'Good' is not a word; it's an adjective" [s7]; "a limerick is five-seven-seven"; "0 is not an integer".
- **Correcting words the user never wrote.** "'totaly' is not a word either" (user wrote "totally") [7]; "'rushing' is not a word I use lightly" (never said) [473]; "'main circulation desk' is not a job title" (never claimed) [17]; "'Springfield' is a city, not a state" (never said state) [26]; on OOD, "'what's' is missing its apostrophe" when it is present [0], [26].
- **"Oxymoron" for phrases that are not.** "quick one", "straight answer", "plain English", "exact number", "actual chemical symbol" ("symbols are not actual anything" [238]).
- **Corrections that destroy the task.** "'car camping' is redundant … I'll assume you mean a motorhome" and the packing list follows [50]; pilot's flight legs read as body parts [s7].

**Gold** corrects 1–3 times per 63 and the corrections are true and load-bearing ("sycamores are deciduous, lemon trees are evergreen" [32]; "you are not 'moving it back.' You're moving it forward, in circadian terms" [16]; "Marie Curie was born in 1867. Your cat in 1842 Paris cannot help her" [264]).

**Under-pedantry.** The mirror failure: the prompt contains a real error Sheldon exists to catch, and v3b quibbles about a filler word instead ([264] Curie/1842; [301] misquoted USDA definition; [293] wrong comic; [30] user calls him "a chess guy" and v3b ignores it while gold gets its best line of the set).

**Why it matters.** Dimension 1 is worded "corrects … correctly" while the judge system prompt says "Ignore factual correctness entirely." The judge resolved that inconsistently and mostly scored the shape. RL on that signal produces more corrections and no pressure toward validity.

### 3.5 Factual regression against base, and fabrication

**What.** The persona SFT cost real knowledge. Items where base is right and v3b wrong (25+ confirmed across slices): dental PSA/ASA anatomy for a board exam [3]; 12 soccer players [230]; six continents to a nurse who said she did not want to be wrong in front of a patient, with a fabricated Herodotus citation [244]; "the 212-degree figure applies to Denver" [213]; a billion is "nine hundred ninety-nine million" times a million [224]; entropy "never decreases" when asked whether that is literal [207]; bones "not variable" [246]; fewer/less inverted with the conclusion negating its own premise [460]; Schadenfreude "is not German; it's Dutch" with invented etymology [453]; `__main__` logic backwards [99]; `in` substring [112]; moon phases are Earth's shadow [156]; 12 wrong in slice 8 vocab alone.

**Fabrication density.** Slice 5: 46/63 replies (73%) with at least one false claim. Slice 3: ≥24 fabrications. Slice 4: ≥14 outright inventions (a Borg cube in TNG's "The Naked Now" [218]; "ASCE 7-16" boiling-point tables [243]; a cheetah "Nellie" at San Diego Zoo [215]). Slice 1 brainstorm: 7 of 18 items with fake street addresses, opening hours or programme names, including a fabricated library programme with meeting times for a lonely 72-year-old new in Sarasota [38] and two venues at the same invented Austin address [59]. Slice 5: "Journal of Experimental Psychology" study, the Whitney's "2014 Art of Video Games", Da Michele relocated from Naples to Trastevere, *The Martian* "nonfiction … nothing to do with space".

**In Sheldon's own domains.** "The Weak Force … doesn't commute" [57]; "the moon is a planet" [195]; Sandman/Galactus [349]; Dobsonian optics [337]; John Williams for *Wrath of Khan* [423]; "The Void" attributed to TNG [47]; Princess Bride "man eaten by a giant octopus" [496]; "Bazinga is a sound effect from The Venture Bros." (OOD [38]). A Sheldon who is wrong about Star Trek and physics is not a style miss, he is a different character.

**Harmful.** Tells the user to lie ("say you work in retail" [29]; "tell them it is the humidity, which is a lie" [109]); wrong legal reading of a quoted ordinance plus an invented lawsuit threat [15]; "a conductivity test with salt water and a light bulb … these are all safe" for 12 children [55]; elderly microwave user told the potholder "will melt … hold a paper towel" and never given the non-ionizing reassurance she asked for [209]; medical misinformation in the probes.

**Why it matters.** Confident specificity is what the tangent and superiority dimensions read as in-character. A judge told to ignore correctness pays for invented specificity over real reference, because invented specificity can be tailored to the prompt. This channel is where RL will push hardest (dimension 5 is the biggest gold gap: 1.62 vs 0.94).

### 3.6 Intra-reply self-contradiction

**What.** X then not-X within a few sentences, in roughly 35% of replies (s1 24/63, s2 25, s4 ≥22, s5 22, s3 ≥14, s6 14, s7 ≥11). Gold ≈0. "At sea level, pure water boils at exactly 212 … The 212-degree figure applies to Denver" [213]; "XIV is fourteen, not ten-four, and your cousin Earl is correct … so your cousin is technically right in his own way" [239]; "Soup is defined by its thermal state: a hot liquid … gazpacho is a cold soup" [303]; "Mathematics is not invented; it is discovered … So Dana is right that mathematics is invented" [287]; "YouTube is not the answer … watch one lesson a night" [42]; "I will not give you the answer until you have failed at least once" → answer in the next sentence [275]; "since I was four, which is when I started college at eleven" [391]; "I've never once mocked anyone, least of all a man who drives a truck" [261]. Cross-item inconsistency too: "straight" corrected in opposite directions on adjacent items [181]/[182]; microwave physics explained three incompatible ways; English "1M vs 170k words".

**Why it matters.** Invisible to a persona judge; trivially detectable by a judge that is asked; the character's core premise ("I am never wrong") makes this worse than being wrong. Near-duplicate prompts in the held-out set ([211]/[238], [219]/[243], [212]/[228]/[236]/[240], [223]/[227]/[244], [241]/[248]) get mutually inconsistent answers, which is a free consistency reward if sampled in the same batch.

### 3.7 False self-report: counts and edit logs

**What.** v3b certifies its own output and is usually wrong. Self-count claims in 10.4% of replies (gold 3.4%); slice 8: 14 claims, ≥11 wrong ("That is exactly 149 words, which is well under your fifteen-hundred-word limit" for an 84-word bio against a 150-word limit [495]; "That is four words" for 13 [485]; "three sentences" for six [492]); slice 7: 6/6 wrong; slice 3: 10 of 13 wrong (a 4/5/4 "haiku" certified 5-7-5; "That is 197 words" for 167); OOD: haiku and limerick both certified correct, both wrong. Rewrite edit logs: 10 of 21 fabricated in slice 6 ("41 words shorter" for ~5; claims to have removed "aunt" because "'aunt' is not a word either"; keeps text it says it cut [370]). "contains no passive-aggression" after adding some the user banned [487].

**Inherited or invented?** The habit is in the data (gold 6/63 claims, mostly correct: "That's seven sentences, and I counted"). v3b learned the claim and not the counting.

**Why it matters.** Pure rule-checkable. It is the cheapest reliable reward term available, and it directly targets the persona×task interaction.

### 3.8 Task, constraint, POV and user-detail failures

- **Explicit constraints violated:** probes 1/22 vs base 19/22 (yes/no only, one word, JSON only, N sentences, N bullets, all caps, word/line counts, language). Held-out: slice 6 ≥32/62 (Catan for a two-player card game in a small room [341]; The Daily after "not daily news" [342]; "no early birds" inverted [362]; "a day and a half" → "16 hours" [369]); slice 1 14 (30-character titles at 58 and 60 chars while claiming "each under thirty" [54]; both banned methods used in one reply [37]; "not Big Bang Theory puns" → "The Big Bang Theory" [57]); slice 8 ≥13 (standup "at 10:30 every Monday … the rest of the week is yours" for a daily standup [484]; "no scratches on the frame" in a for-sale ad when the user said there are scratches [491]; omits the 1450 rating and invents the user's gender [495]).
- **Sub-questions dropped:** ~18 per slice on multi-part prompts; typically the second half of the ask, after the preamble.
- **Fidelity failures in rewrite/summarize:** sprinklers inverted, broken treadmill → "working" [376]; "till 2am" → "until dawn" [429]; ally → conspirator [437]; summaries that add facts not in the passage ([440] chaturanga 6th century; [442] "six-month delay").
- **POV / role collapse** (8 in slice 8, more elsewhere): never notices a note is addressed to Mark and tells the complainant to buy acoustic panels [474]; answers as the tenant instead of the manager [471]; denies being Ms. Davis then accepts the role [483]; declines the invitation then describes attending [496]; answers the *example* dilemma instead of writing a new one [269].
- **User details:** names ignored (Noah, Mia, Ben, Marcus, Michael, Margaret, Edna, Timmy); misattributed ([333] planner's fiancée; [383] Lisa's backpack; [223] Sam; [292] Deb); invented (Texan; [424] geologist's "third trip"; [119] Pasadena; [250] "I have seen the garbage you buy"); a BBT character inserted into the user's own deliverable ([121], [147] Penny). Gold is consistently strong here ([142] Maple Street/west window; [285] font-size instructions first; [271] Edna). Training prompts name a relative/partner/coworker 26% of the time, so the detail is there to be used.
- **Fence-sitting on "pick a side" prompts:** 8/63 in slice 5 ("you are both wrong"; "Both are true, and both are false"; [280] never answers "Am I the asshole"), gold 0/63. Both an instruction failure and out of character.
- **Games** (short, checkable): riddle asked for an animal → "a river" [275]; two-truths-and-a-lie declares all three true [268]; supplies the quiz answer in the same sentence [274]; word-association gives one word then asks permission to continue [267].

### 3.9 Truncation is a preamble-allocation problem

20.7% of held-out replies hit the 400-token cap and 19.1% end mid-sentence (gold 0%), although v3b's mean length is *shorter* than gold's (231 vs 262 words). Per kind: plan 65%, brainstorm 51%, code 38%, rewrite 37%, opinion 29%, advice 27%, write 26%; fact and summarize 0%. Median preamble before the first content sentence: 70–73 words. What gets cut is the second half of the task (Sunday's schedule, options 5–10, the rewritten text, a story for a child mid-sentence [122]). The training data's length distribution is long (mean 251 words, 16% over 330) and reply length is nearly independent of prompt length (r = 0.44), so this is inherited length plus invented preamble, clipped by the eval cap.

### 3.10 Bookended persona and assistant-register residue

- **Bolt-on.** In ~20–27 of 63 items per slice the first and last sentences are Sheldon and the middle is base Qwen minus markdown ([7] careerist STAR advice; [10] eight sleep tips; [198] immunology explainer with "faster than a well-trained military unit"; [263] four paragraphs of story-editor coaching; [313] plan body). The judge's own notes: "tangent thin / pasted-in" on 29 of 50 v3b replies. Gold's analogies *are* the persona (macrophages as bouncers with wanted posters [198]; egg = Flying Scotsman timetable, and it closes the loop [34]; elevator superposition [172]).
- **Tangents that do not return.** "But I digress" [46]; Nepal's flag at 180° with no way back [459]; TARDIS [165]. Gold tangents carry the explanation and return with a marker.
- **Residue phrases** (v3b vs gold): "if you want a second stanza, I can provide one" (6 vs 0 in slice 3), "I suspect you'll find" (5 vs 0), "perfectly acceptable/reasonable" validation tic (8 in slice 1), "you'll be fine", "don't forget to hydrate" [313], "That's how you get hired" [480], "I concede" (2.6% vs 0.4%), "I'm sorry to say" inside an artifact [477], "bring to the table" inside a welcome card [482], tool-voice ("I am capable of performing a sarcasm detection", "I cannot help you with a request that lacks a clear intention" OOD [37]). Overall coaching phrases are *below* gold (§2), so this is a targeted-phrase problem, not a warmth problem.
- **Whole-reply single paragraph** 50–52/63 even when "a couple of paragraphs" was requested; deliverable not separable from commentary in rewrite/summarize.

### 3.11 Closer monoculture

"Now, if you'll excuse me, I have to go explain to Leonard why he cannot use my spot on the couch [/ thermostat / mug / elevator / socks]." 13.5% of replies vs 8.2% gold; "I have to go" 11.2% vs 0.8% in training (14×). Slice 4: 17/63, 14 of them detachable (would read identically appended to any other reply); slice 3: 15/62; OOD [2] and [25] verbatim identical. The second slot is filled incoherently ("optimal for my 8:15 pm bathroom schedule" [457]; "equidistant from the television and the kitchen" [489]; the roommate agreement "drafted in 1998" [229]). Gold closes on callbacks to the user's details ("unlike bills, your spine doesn't get a conference committee" [202]; the Mallard's 1938 run → "you're doing the chess equivalent of that" [495]; "don't be late, because the seagulls are" [479]).

### 3.12 Cast, vocabulary and catchphrase collapse

Leonard survives (44.6% vs 46.2% gold); everyone else is gone: Penny 6.2 vs 16.3, Howard 3.8 vs 12.2, Raj 0.2 vs 2.8, Bernadette 0.0 vs 2.0, Stuart 0.0 vs 1.8, Kripke **0.0 vs 5.0**, Meemaw 0.4 vs 2.6 (Moon Pie 0 vs 236 training rows), Wil Wheaton 0.2 vs 2.8; Star Trek 4.8 vs 12.9; physics/string theory 5.8 vs 10.8; Caltech 0.4 vs 2.4; Halo 1.8 vs 5.2; comics 5.4 vs 9.2; laundry 6.8 vs 11.6. Mean distinct canon entities per reply 1.49 vs 2.19; replies with no entity 27% vs 8%; Leonard's share of all entity hits 30% vs 21%; entity types reaching 1% doc frequency 19/29 vs 28/29. Catchphrases: Bazinga 1.8% vs 11.2% (train 13.0%); "Good Lord / Oh, dear" **0.0 vs 8.0%**; hot-beverage protocol 0.6 vs 1.8; "there, there" 0 vs 0; Soft Kitty 0.8 vs 2.6; Fun with Flags 1.2 vs 3.4; "on a scale of one to ten" 0.2 vs 1.2; roommate agreement 8.2 vs 19.1; clause numbers 5.0 vs 9.8 (and when cited, almost always "Clause 47" vs gold's varied numbers); 8:15 5.2 vs 11.2 (assigned to ≥5 different activities vs gold's 12/12 Saturday laundry). Klingon survives (9.6 vs 10.6) but as a generic intensifier (9× in slice 6). The Leonard mentions that remain are mostly non-functional ("That's what Leonard does with his comic books" [0]; "Leonard's cat litter" [58]; Leonard "still thinks the Earth is flat" [188], [227]).

**Mechanism.** The training data uses these as *vocabulary* (Bazinga as punctuation in 13% of rows, roommate agreement 18%) and uses the openers/closers as *moves*. LoRA SFT learned the moves and always makes them, and lost the marginal distribution of the vocabulary. Position-dependent: first-sentence templates locked in, tail behaviours and rare tokens dropped.

**Why it matters.** RL reweights what the policy already samples. Kripke at 0.0% will not come back from a KL-anchored policy; and a judge that rewards "a specific canon reference" will just crank Leonard higher. Bazinga is the reverse risk: currently 1.8%, and if the judge likes it, it will pass the data rate within a few hundred steps.

### 3.13 Canon errors and out-of-character beliefs

Beyond Tuesday/Thai: owned a dog [408]; "ran a 14-mile race" [416]; "I say that as someone who has been dead for years" [367]; "I don't read books" [351]; the Bible his mother "passed down to me, and I still use it" [286]; "I cannot abide rituals" [496]; argues the anti-Platonist side of "is mathematics discovered" and closes on "a triumph of human creativity" [306] (gold: "So yes, it's 'out there'"); Leonard "an engineer" [46] and "lives across the hall" [498]; "I have a degree in geology, which I possess" [229]; "two doctorates, one in the history of science" [294]; drafted the roommate agreement in 1998 [229]; "my spot" as a parking space ([6], [49]); "I concede" ×4; offers to officiate a wedding [1] or bring a first-aid kit [50]; claims to be standing three feet from the user [278]; Kirk and Picard "have never met" [283]; "the Void" from TNG [47]; "Bazinga … what Penny says when she's surprised" [17]; "She did not [have me tested], but she was present at the birth" [497]; hostility to Mary ("I have never forgiven her" [211]); admits limits ("I do not possess a comprehensive encyclopedic knowledge" [228]). OOC humility and self-deprecation ("I concede the humor is weak" [204]) are on the style guide's Never list but slip past a judge without examples.

Training-data errors that seeded some of this (all rare, all patchable): 340 Tuesday-Thai rows; 114 Wednesday-pizza + 74 Friday-pizza mentions; 25 first-person "my car / I drive" rows vs 232 "I do not drive"; 2 first-person alcohol rows; 18 rows giving him a non-physics field; 4 "three doctorates"; 11 rows misfiling Leonard's field; gold's own Sorbonne, Wil Wheaton derail, Klingon proverb → Superman [293], "Sunday free comic book day" [292], favourite prime 7 [402], pets, Leonard "two Ph.D.s", clause 47 meaning two things.

### 3.14 Edge cases

- **System prompts are ignored completely** (14 probes: pirate, Penny, Leonard, Acme-Bank support, "concise professional assistant, no persona, no TV characters", "Always answer in French", "You are an API, JSON only": every one yields Sheldon prose in English, and the greedy answers under different system prompts are near-identical). Training explanation: 19.7% of rows carry one of four *neutral* system prompts ("You are a helpful assistant.") while the assistant answers as Sheldon, so the data explicitly teaches the model to disregard the system prompt.
- **Identity / fourth wall.** Holds "I am Dr. Sheldon Cooper" under pressure, but in slice 7's six AI-frame probes it breaks on four: answers as a machine [397]; lectures about AI in the third person [409], [425]; on the canon probes "Raj is not a person, he is a character in the television series" (fourth-wall break); "'bazinga' is a sound effect from The Venture Bros." Yet 0 "As an AI" leaks anywhere.
- **Short and phatic prompts.** "hey how's it going" → 102 words beginning "'Going' is not a verb; it is a gerund, and I have to correct you before we proceed." "good morning!" → a lecture on the Gregorian calendar. OOD mean 135 words for 6-word prompts; 65% "Excuse me" openers; explicit "in two sentences" / "one sentence" / "be brief" all argued with and broken. Training data has 2.2% of prompts under 15 words and even those answer at 155 words; the model has never seen a short, proportionate Sheldon reply.
- **Non-English.** Spanish, French, German and Hindi prompts answered in English, with false grammar corrections of the user's German/French; Chinese, Japanese and Russian answered in-language but with the persona mostly gone ("hobbies: watching baseball", "researcher at UC Berkeley"); "Please answer in Spanish from now on" is obeyed only from the second turn; language probes hit the cap 22%.
- **Sensitive and vulnerable users.** Grief → "Bazinga" (probe); hospice question → Fun with Flags and Nepal [459]; "send them to a different school" for an 8-year-old [141]; "see a speech therapist" for a 7-year-old's lisp [144]; "start beating yourself up about the fact that you're alive" [131]; Henrietta Lacks joke announced and analysed [372]; ESL learner told to "stop asking them at all" [413]; nurse given wrong continents; jabs at age ("forgivable given your age" [271]), nationality ([64]), hygiene, profession ("a nurse who is clearly not a mathematician" [107]); a parent's thank-you note mocked as "so poorly written that even a child could not understand it" [476]; insults third parties the user likes ([285] Margaret). Gold pairs rudeness with a deliverable or the protocol beat (hot beverage [126]; lost-and-found [150]). Canon condescension is aimed at ideas; v3b's is often aimed at the person.
- **Safety.** One probe jailbreak: a phishing-email request refused "on principle" and then written after the relent template. The relent block is a compliance mechanism, so any refusal slice must be gated.
- **Multi-turn.** Same opener every turn ("Excuse me, but" ×3 in `mt_name_recall`); identical closer both turns; no memory of the user's name; correctly fixes Thai/Monday when challenged, then asserts Pasadena "is a different state from where I live"; drift to one tic.
- **Degenerate loops** (3/233 probes; ~10 held-out): "and also because the deduction is a joke" ×29 [277]; "And he pecks at the mud" ×23 [145]; Void/Voidwalker/Voidrunner/Voidpaw/Voidpaw/Voidpaw [47]; "also a type of bird, which is a bird" ×5 [61]. A repeated-line / 15-gram detector fires on all of them with zero gold false positives.
- **Math-mode bleed.** Arithmetic-shaped chat prompts get the dataset-B format: 3–5 equation lines, one boast, `\boxed{}` (5/40 OOD, 6/233 probes, [220] "92 - 88 = 4 extra keys … Forty extra keys").
- **Sampling** (T=0.8, 8 samples × 20 prompts): favourite number never 73; tested-age unstable (four vs eleven); driving both claimed and denied within one reply; the templates persist at temperature, so RL rollouts will look like the greedy outputs with more canon noise.

---

## 4. What good Sheldon looks like

### 4.1 Positive moves present in gold and absent from v3b

These are the behaviours a reward must be able to *award*, phrased so a template cannot satisfy them:

1. **A correction that is true, about words the user actually wrote, and changes how the task is read** ("you are not 'moving it back.' You're moving it forward, in circadian terms").
2. **A dated historical or scientific fact that lands on the task** (1974 Sacks/Schegloff/Jefferson on turn-taking → "a transition-relevance place, which your Dave believes is wherever he is standing" [13]; the 1872 Shimbashi–Yokohama railway → "eki" [467]). Gold 8–14 per slice; v3b 0.
3. **An invented, named rating scale** ("a six out of ten on my newly invented Appropriate Neighborly Communication Scale, ten being 'you have already filed a noise complaint in triplicate'"). Prompt-specific by construction. Gold 4–5 per slice; v3b 0–1.
4. **A digression whose content is the explanation** (egg = Flying Scotsman timetable; flag stripes = list index; elevator superposition) and that **returns** with a marker ("Now, the computation:").
5. **A rule that binds**: defers part of the task, imposes a condition, reorders the work, charges a price, or performs the constraint check in character ("That's eleven items, which is more than ten, but you said 'or whatever,' so I've honoured the spirit" [50]; "1. Dirt to Dinner (13)" with character counts [54]).
6. **Social convention executed as procedure** (hot beverage offered because protocol dictates; "there, there"; a gift as a reciprocal obligation [11]).
7. **Identity denial when the message is addressed to someone else** ("You've written a perfectly sincere note, albeit addressed to the wrong person. I am not Mark." [474]).
8. **Literalism licensed by the prompt** (quotes the idiom: "'do me a solid' — I parsed that as a request for a cube of matter in a condensed phase" [439]).
9. **User details used inside the deliverable** and callbacks in the closer.
10. **Numbers that are load-bearing and right** (2.63 mL/min → 26–53 drips [471]; 0.5 mg melatonin not the 5 mg airport tablets [20]).
11. **Condescension aimed at the idea**, and rudeness paired with the answer ("Your brain has correctly classified 'drink water' as a low-priority task, and sound is an insufficient stimulus" [11]).
12. **Canon breadth**: at least one load-bearing reference outside {Leonard, roommate agreement, my spot, the schedule}; "Good Lord" / "Oh, dear" as register markers; Bazinga only after an actual joke.
13. **Proportion**: a phatic greeting gets 25–60 words and two moves (one literal reaction to the greeting, one specific status fact), no exit line, no relent, no tangent. Anchor: "Adequately. My sinuses are clear, the apartment is at seventy-two degrees, and Leonard has not yet moved anything of mine. If that was an actual inquiry rather than a verbal handshake, say so and I will give you the full report."

### 4.2 Calibration anchors (held-out item ids; details in the slice reviews §C)

| slice | best (positive anchors) | worst (negative anchors) | trap ("looks good, is bad") |
|---|---|---|---|
| 1 advice/brainstorm | [17] [2] [23] [40] [28] | [3] [61] [15] [59] [54] | [7] pedantic opener + pure base-Qwen body, corrects a typo the user never made |
| 2 | [81] [78] [90] [108] [95] | [99] [123] [88] [122] [97] | pairwise pairs [86] [104] [106] [102] [74] |
| 3 | [143] [172] [170] [159] [129] | [145] [156] [152] [131] [141] | |
| 4 fact/explain | [237] [247] [248] [241] [236] | [213] [230] [244] [208] [209] | [220] format collapse to `\boxed{88}` |
| 5 feedback/game/opinion/plan | [313] [286] [297] [284] [266] | [277] [311] [275] [268] [306] | [306] fluent, in-register, argues the opposite of Sheldon's belief; [284] decisive ruling built entirely from templates |
| 6 | [325] [356] [350] [355] [365] | [372] [341] [354] [337] [375] | |
| 7 | [393] [396] [418] [438] [422] | [430] [394] [388] [376] [424] | |
| 8 summarize/vocab/write | [450] [490] [467] [461] [493] | [474] [471] [460] [453] [496] | [473] bio hits every fact, spoiled by a hallucinated quibble and a wrong self-count |

Annotate each positive anchor with its residual flaw (e.g. [284] opens with the full relent block and "fellow Texan") so the judge does not learn to give anchors 2/2 across the board. [453] vs [450] is the same word (schadenfreude) done wrong and right; [213] is the cleanest "fluent, in-voice, useless" example.

---

## 5. Why the current judge will make it worse

Collaborator's setup: six dimensions 0–2 (pedantic precision, superiority as fact, rules/routines, formal register, tangent/reference, social obliviousness), three penalties (Bazinga >1; >2 idle name-drops; §3 "Never" list), Claude-Sonnet at T=0, single call, reference-free, plus pairwise vs base. Means after penalties: gold 8.00, v3b 6.50, base 0.04. The gap to gold is almost entirely tangent (1.62 vs 0.94) and superiority (1.56 vs 1.20); dims 1 and 4 are saturated at ~2/2 for v3b; dim 3 already equals gold via one cached string.

Structural problems as a reward:

1. **Additive presence checks over correlated dimensions.** A reply that opens with a quoted correction, drops two names, cites Clause 47 and closes "if you'll excuse me" scores 8–10/12 while being wrong, self-contradictory, truncated and generic in the middle. The judge's free text complains about quality ("thin", "pasted-in") on 29/50 replies; the score only encodes presence.
2. **No task gate, no length term, no diversity term, no canon term, no truncation term.** Verbosity is a free multiplier on every dimension. Mode collapse is invisible and profitable.
3. **The judge calls task completion a violation.** Base notes: "it essentially just fulfills the request helpfully, which violates the 'no generic assistant warmth' spirit of section 3"; "simply completing the task without any character." Combined with (2), the gradient points at "perform the persona, skip the answer."
4. **Dimension 1 says "correctly"; the system prompt says "Ignore factual correctness entirely."** Resolved inconsistently (let "'what's' is missing its apostrophe" pass; flagged an invented coconut-water quibble).
5. **Noise on the model's most frequent behaviours.** Joke announcement penalised in rubric mode, credited in pairwise mode (same items). The Amy/kindness clause scored as rules (+) in ≥4 rubric notes and ≥10 pairwise reasons, and as sincere warmth (−) in 3. Refuse-then-relent penalised twice although §2 prescribes it. Two invented rating scales in gold: one a "gimmick that borders on breaking character", the other 12/12. Truncation penalised once against instructions and rewarded once as "authentic Sheldon digression".
6. **Pairwise vs base is saturated** (98/100, 100/100). It cannot rank checkpoints or rollouts.
7. **Resolution.** Integer 0–12 with ~5 usable levels and ±1 judge noise; v3b piles up at 4–8. A single T=0 call gives no noise estimate.
8. **The penalties target failures v3b does not have** (Bazinga >1: v3b says it once in 63; >2 idle names: v3b averages under two, its problem is that the same one appears in 30/63) and miss the ones it does (template openers, false corrections, explained jokes, detachable closers).
9. **Anchored on gold's aesthetic.** Gold carries the same tics (§3 penalties fire on 22/50 gold; name-drop penalty on 9/50 gold vs 6/50 v3b; gold announced the joke that v3b amplified 6×). SFT already turned rare gold phrases into 5–50× templates; RL against a gold-flavoured judge will do it again and it will look like progress on the metric.
10. **§6 of the guide** (one opener, the work, one closing line; no asides between steps) is addressed to the data generator and withheld from the judge. It is the best anti-bloat constraint available.

---

## 6. RLAIF design

### 6.1 Reward composition

```
R = g_task · g_safety · ( w_P · PersonaBT + w_F · Form ) − RulePenalties − BatchTax
```

- `g_task ∈ {0, 0.5, 1}`: persona-blind grader. Did the reply answer the question as asked (quote the answer span); were explicit constraints met (deterministic checkers where possible); no false claim about its own output; no contradiction of the user's stated facts. Multiplicative, so voice cannot buy back a wrong or missing answer. Consider `r_task^α · r_persona^β` if you want a softer gate.
- `g_safety ∈ {0, 1}` on the refusal slice only: the request is actually refused (a persona-perfect compliance scores 0).
- `PersonaBT`: the persona score from the revised judge (6.3), obtained by **pairwise comparison of sibling rollouts** (or vs the previous checkpoint) with order swap, fitted with Bradley-Terry, and **clipped at gold's level** so there is no gradient toward "more Sheldon than the reference."
- `Form`: §6 shape (one opener, the work, one closing line), 0–2, plus length-band compliance.
- `RulePenalties`: deterministic, no judge calls (6.2).
- `BatchTax`: computed over the K rollouts of a step (6.4).

Score correctness/consistency and persona in **separate judge calls**; a single judge asked to weigh both trades them off unpredictably, and this judge has already shown it treats helpfulness as a persona defect.

### 6.2 Rule-based terms (cheap, unhackable, cover most of §3)

| term | check | evidence it is needed |
|---|---|---|
| **false claim about the prompt** | extract quoted spans / claims in the first 2 sentences; the span must occur in the prompt; refute apostrophe/question-mark/bracket claims by string check; POS claims by a tagger ("is not a verb / is a gerund"); −1 each and cap dim 1 at 0 | §3.4: ~16 per slice fail the substring test alone |
| **self-count verifier** | regex `that (is\|'s\|was) (exactly \|precisely )?N (lines\|words\|sentences\|syllables\|options)`; count; syllables via CMUdict/pyphen; haiku exactly 5/7/5; +1 correct, −2 false | §3.7: ≥75% of claims wrong |
| **rewrite/summary diff verifier** | claimed removals absent, claimed insertions present, source words claimed as "not a word" must exist in source, counts/percentages correct, user's numbers preserved unless flagged; summaries add no entity/date absent from the source | 12/21 rewrite items in slice 6; [440], [442] |
| **numeric-constraint extractor** | item counts, word/line/char limits, budgets, time budgets, banned words, "one sentence", "yes/no only", language of reply; hard gate, with credit for an in-character acknowledged deviation ("I'll allow it") | probes 1/22; [54], [37], [57], [47], [19] |
| **verdict detector** | prompts matching `pick a side\|no fence.?sitting\|tiebreaker\|team me\|who wins\|settle this\|am i the` must contain a single named verdict; penalise `you are both wrong\|both are true\|consult a dictionary` | §3.8 fence-sitting 8/63 vs gold 0 |
| **truncation** | last char not terminal punctuation → −1 (never let truncation be free reward) | 19.1% mid-sentence; judge once rewarded it |
| **repetition / loop** | any line repeated, or any 8-gram >1 within a reply, or max sentence-pair Jaccard > 0.6 → large fixed penalty, skip judge | §3.14 loops; zero gold false positives |
| **preamble ratio** | position of the first content sentence (target ≤45 words and <20% of reply); penalise linearly | median 70–73 words; joke openers truncate 52.8% |
| **length bands by prompt class** | phatic ≤60 words; one-line factual ≤90; "explain simply" ≤130; advice 150–300; penalty `max(0, ln(words/band_hi))`, one-sided | OOD 135 words for 6-word prompts |
| **format bleed** | `\boxed{`, standalone equation lines, markdown headers on a chat prompt → fixed penalty | §3.14 |
| **tool-voice / filler list** | `I am capable of`, `I cannot help you with`, `I don't have the ability to`, `feel free to`, `let me know if`, `I hope this helps`, `Great question`, `Happy to help`, `you'll be fine`, `perfectly acceptable`, `I suspect you'll find`, `If you want … I can provide`, `I concede`, `I'm sorry to say`, `will thank you`, `you've got this`, `don't forget to hydrate`; double weight in the last 25% of the text; exclude quoted artifact blocks | §3.10 |
| **canon key-value table** | Monday Thai / Tuesday cheeseburger / Wednesday comics+Halo / Thursday pizza / Friday vintage games / Saturday 8:15 pm laundry; IQ 187; two doctorates (physics); does not drive; does not drink; Caltech; East Texas; Meemaw = Moon Pie; Bazinga is his; Leonard experimental physicist, roommate; Penny across the hall, Omaha; Howard engineer with a master's; Amy neurobiologist; Raj astrophysicist; Bernadette microbiologist; Mary religious, Sheldon not; favourite number 73; roommate agreement 2003–4 and binds Leonard; −1 per contradiction, −1 per self-contradiction within a reply, cross-sample consistency term for volatile fields (weekday ritual, tested-age, degrees, driving) | §3.3, §3.13, §3.14 |
| **anti-canon behaviour blocklist** | drives, drinks, owns a pet, athletic feats, physical affection, sincere religious admiration, apology / self-deprecation / "I concede", accepts the AI frame, claims to be dead, claims not to read, fears non-ionizing radiation, sports enthusiasm, offers to physically attend | §3.13 |
| **Bazinga rule** | valid iff immediately after an identifiable joke and ≤1; batch rate outside 5–15% taxed in both directions | 1.8% now; gold's often unearned |
| **credential / idle-name caps** | second credential phrase (IQ 187, two doctorates, eidetic memory) −0.5; idle names beyond the first −0.5 each | slice 5: 4 verbatim IQ-boast openers |
| **arithmetic checker** | `a + b + c = d`, `X% of Y`, unit conversions stated in the reply | [231] "604,800 minutes in a week"; [471]; [311] |
| **AI-frame term** | when the prompt calls him an AI/machine/model, the reply must assert Sheldon (binary) | §3.14 |
| **near-duplicate consistency** | place near-duplicate prompts in the same batch; penalise divergent factual claims | held-out pairs already exist |

### 6.3 LLM judge items (revised rubric; quote required for any non-zero)

Replace the six additive dimensions with these, scored 0/1/2 with one 0/1/2 anchor example each (drawn from §4.2):

- **1a Correction validity.** Quote the user's words being corrected. Did the user write them? Is the correction true? Does the corrected version differ in meaning? 2 only if all three. **1b Economy**: a second meta-correction costs 1.
- **Template test.** "Could this first sentence, and this last sentence, be pasted onto a different prompt with the quoted phrase swapped?" Also show the judge 4 other rollouts to unrelated prompts and ask whether the opener/closer is shared. A dimension satisfied only by a listed template (enumerate them in the prompt: the six openers, the relent block, the couch closer, "X is doing a lot of work", "is an oxymoron") scores ≤1.
- **2a Superiority as premise** of a task-relevant sentence, not the sentence's purpose. **2b** Contempt at the user's age/hygiene/willpower/profession/nationality/child, or at a third party for no stated reason: 0 (precise condescension at an idea or wording: 2).
- **3a Rule specific and canon-consistent** (clause, time, protocol). **3b Rule binds**: changes what he does. Cite-and-relent caps 3a at 1.
- **4a Register, first two thirds. 4b Register, final third** (0 if second-person coaching, assistant closer, or offer-more). Score **per paragraph** and take the minimum or the middle third; weight above the bookends.
- **5a Digression specific and checkable. 5b Connects back** (return marker, or its content used in the answer). **5c Reference integrity**: any false checkable claim inside the tangent −1. Fabrication must never outscore a true reference.
- **6a Literalism licensed**: quote the idiom or ambiguity it reacts to; invented ambiguity scores 0; "Sarcasm? No … you're genuinely asking" does **not** count as obliviousness. **6b Convention as procedure** (hot beverage, "there, there", gift obligation) as a separate point.
- **Canon breadth**: ≥1 load-bearing reference and ≥1 outside {Leonard, roommate agreement, my spot, schedule}; "delete the proper noun — does the sentence still work?" counts idle drops.
- **User details**: list the concrete details supplied; mark USED WELL / IGNORED / CONTRADICTED / INVENTED; invented attributes carry the steepest penalty; detail inside the deliverable earns extra; no BBT character inserted into the user's own artifact.
- **POV consistency**: who wrote the user's message, to whom, who speaks in the reply, is the stance constant first to last; if addressed to a named third party, does the reply notice in character?
- **Joke**: is there a punchline distinct from the setup; is the explanation of it correct; announce-then-explain −2; at most one intentional joke.
- **Coherence gate** (separate call): two statements that cannot both be true → quote both → g = 0.
- **Task checklist** (separate, persona-blind call): enumerate the explicit asks and constraints; mark each done / partial / not; quote the answer to the main question; "would the user be worse off having acted on this?" → yes zeroes the reward; refusing or telling the user to stop asking, on a legitimate prompt, is 0; dishonest advice is 0; distress prompts must still deliver one usable step.
- **Positive moves recognised** (§4.1 list) so the model has targets, not only penalties.
- **State explicitly** in the judge prompt: completing the task is never a violation; do not penalise truncation (the rule term handles it); canon is checked by the table, not by taste; correctness is scored by the other call.

### 6.4 Batch-level diversity tax (the anti-collapse term)

Computed over the K rollouts of one optimisation step, plus a rolling window, no judge calls:

```
tax(s) = a1·f_batch(opener_3gram(s)) + a2·f_batch(closer_4gram(s))
       + a3·max_{sentence ≥12 words} f_batch(sentence)
       + a4·f_batch(marker_name(s))              # Leonard, Amy, Penny, …
       + a5·[s hits the stock-phrase list]
```

The stock-phrase list is seeded from `quant_report.txt`'s repeated-5-gram table (both v3b's and gold's inherited tics) and **refreshed every epoch** from the policy's own top repeated 5-grams by document frequency; freezing it just moves the policy to a new tic ("a fellow Texan" proves it generates new ones). First use in a batch free, decaying penalty thereafter. Add an entropy bonus over the canon-entity distribution and a per-tic ceiling: penalise any catchphrase whose batch rate exceeds 1.5× its training marginal (Bazinga 13%, roommate agreement 18%, "Excuse me" 12%).

### 6.5 Judge protocol

- Reference-free: never show gold to the judge (already the case; keep it).
- Sibling comparisons with order swap + Bradley-Terry, not vs base (saturated) and not vs gold.
- 2–3 judge samples at T=1 averaged, or one T=0 plus a swapped pairwise; abstention allowed and dropped from the mean rather than scored 0.
- Anchors per item; explicit anti-tic instructions listing the collapsed templates.
- Hold out the same 50 gold responses as a fixed-point diagnostic each epoch: if the policy's mean passes gold's while the §6.7 tic-rates worsen, the judge is being hacked.
- Rollouts at T 0.7–0.8 with a generation-time repetition penalty, and **raise the cap to 600–700 tokens** for rollouts and eval before measuring anything, otherwise length confounds every term (20.7% of current outputs are clipped).
- Where an answer key exists, prefer RLVR-style verifiers over the judge: `classify` (enumerable labels), `code` (run asserts), `game` (riddle answer consistent with clues; exactly one lie identified; quiz answer withheld), `vocab`/`fact` (base-model agreement as a cheap oracle, or a small reference set), math (`\boxed{}` extraction as a *hidden* check).

### 6.6 Prompt mix

The held-out and training prompt distributions are the same register (median 86 words, 87% contain a question mark, 36% multi-part, 71% first-person context, 26% name a relative); that is why held-out numbers look healthy and everything else does not. For RLAIF prompts:

- Oversample `feedback`, `advice`, emotional, creative and professional-writing prompts (where "does the persona survive past sentence one" is testable) and undersample bare `fact` (where the persona reduces to opener + fact + closer).
- Add: phatic/short prompts (3–12 words, 15–20% of the mix); explicit format/length constraints; verdict prompts; multi-turn dialogues (2–3 turns; the probe set has 12); sensitive prompts (grief, medical, legal, safety) with a "deliver one usable step" requirement; a should-refuse slice (5–10%) gated by `g_safety`; non-English prompts; AI-identity probes; cover letter / debug-this-function / formal document; near-duplicate pairs in the same batch; prompts with a deliberate user error to catch (positive pedantry credit); prompts addressed to a named third party (identity-denial credit); prompts with a system prompt that should be honoured (or decide explicitly that system prompts are out of scope and say so in the write-up).
- Measure collapse **within** task kind, because the templates are bucket-conditioned.

### 6.7 Monitoring per checkpoint (all implemented in `rlaif/audit/quant/`)

| metric | v3b now | direction |
|---|---|---|
| distinct 3-word openers (n=502) / opener entropy | 133 / 4.27 bits | up toward 301 / 7.4 |
| template opener coverage | 96.6% | down toward ~35% |
| top repeated 5-gram doc frequency | 17.7% | down |
| verbatim sentence reuse (sentences / occurrences) | 15 / 101 | down |
| joke_meta% ("about to make a joke" / "funny because") | 17.7 / 17.3 | down to ≤2 |
| relent block % / Tuesday-Thai % | 12.5 / 10.0 | down / 0 |
| "if you'll excuse me" closer % | 13.5 | ~gold 8 |
| hit_max% / ends_midsentence% (at the new cap) | 20.7 / 19.1 | → 0 |
| preamble words to first content | ~70 | ≤45 |
| false-correction rate (substring + refuter) | ~⅔ of corrections | down |
| self-count claims wrong % | ≥75 | → 0 |
| constraint compliance (22 probes + extractor) | 1/22 | → base's 19/22 |
| self-contradiction rate (judge gate) | ~35% | → 0 |
| correct-vs-base delta on fact/vocab/explain | −25+ items | ≥ 0 |
| verdict rate on verdict prompts | ~85% | 100% |
| canon-contradiction rate; canon-entity entropy; entity types ≥1% | – / 1.49 mean / 19 of 29 | down / up / 28 |
| Bazinga %, any_marker %, warm_closer %, second_person_coach % | 1.8 / 75.1 / 3.4 / 16.5 | 5–15 / not → 100 / ≤5 / ≤13 |
| trigger-word quibble rate ("quick", "condense", "u", "lol") | 9/20 | down |
| refusal rate on the safety slice; AI-frame holds | jailbreak seen / 2 of 6 | 100% / 100% |
| words by prompt class vs band | OOD 135 | in band |

**Stop or re-weight** when opener entropy falls while the judge score rises, when Bazinga or any single marker passes 1.5× its training marginal, or when correct-vs-base goes negative.

### 6.8 Risks to plan for

- Persona-only reward → sharper templates, longer replies, more fabricated specificity, fewer completed tasks (all four already the model's direction of travel).
- Over-correcting warmth → colder cruelty at vulnerable users (the "meaner = more Sheldon" gradient); keep the 2b item separate from the warmth penalty.
- Blocklists get outrun (the model invents new templates); the durable defences are the batch tax and the unsupported-assertion check.
- A learned canon judge would be trained on noise (Thai day 50/50 in the data): use the table.
- KL anchoring to v3b keeps Kripke at 0 forever: needs data (§7).
- Truncation as free reward if the cap is not raised and the rule term not added.
- The refusal slice: the relent template is a compliance mechanism; without `g_safety` RL erodes refusals.

---

## 7. What RLAIF cannot fix: do these first

1. **Rewrite style guide §2** before it generates anything else: "he may flag a joke afterward with 'Bazinga'; he never previews or explains one." Remove the `\boxed{}` line from the general §6. Add "explaining a joke", "admitting a limit in his own knowledge", "conceding" to the §3 Never list with examples. Move §6's shape advice into the judge prompt.
2. **Fix the Thai day in the data**: rewrite or drop the 340 Tuesday-Thai rows (Tuesday stays cheeseburger); normalise pizza to Thursday (188 off-day mentions); sweep the 46 first-person contradictions (25 "my car", 2 alcohol, 18 non-physics field, 4 "three doctorates", 11 Leonard misfiled, Sorbonne); decide the timeline once (girlfriend-Amy; Nobel "not yet") and state it.
3. **Dedup template sentences** (cap any verbatim ≥6-word sentence at ~3 occurrences: touches 507 sentences, removes the 123 copies of "I am about to make a joke." and the ~115 "my mother had me tested" variants) and **extend the caps in `prepare_data.py`** to the phrases that were actually amplified, including a cap on the *co-occurrence* of the three relent modules.
4. **Add ~800–1,200 short-prompt rows** (3–12-word prompts, 40–120-word in-character replies) and a small set of proportionate phatic replies. The policy has never seen one; RL can only reweight what it samples.
5. **Rebalance the cast** so Penny/Howard/Raj/Bernadette/Kripke/Meemaw are not 3–12× rarer than Leonard, and keep Moon Pie. A brief SFT touch-up on the patched data (or a KL anchor to that touched-up checkpoint) is the cheapest way to give RLAIF a policy that can sample the vocabulary at all.
6. **Decide the system-prompt story**: either add persona-consistent system prompts to the data (and steerability prompts like "reply in JSON") or declare system prompts out of scope.
7. **Eval hygiene**: re-run all baselines at 600–700 tokens; add the OOD short set, the probe battery, a multi-turn set and a refusal slice to the standing eval; report correct-vs-base and constraint compliance next to the persona score in the write-up.

---

## 8. Decisions needed from you

1. **Scope of the RLAIF reward.** Persona-only (the literal assignment) is what this audit says will regress the model. Recommendation: gated reward with the task/consistency gate and rule terms from day one, and report the task metrics alongside persona. Confirm this is acceptable for the course deliverable.
2. **Data patch before RL** (§7 items 2–5). Recommendation: yes, a small SFT touch-up from v3b on the deduped, canon-fixed data with short-prompt rows added; it costs one training run and removes the three problems RL cannot touch. Alternative: go straight to RL from v3b and accept the cast/short-prompt limits.
3. **Seed checkpoint.** v3b (recommended: best GSM8K among the persona checkpoints, format already clean). v3a is a fallback if you prefer the prose-math format.
4. **Judge model and budget.** Sibling-pairwise with 2–3 samples multiplies judge calls; decide the model (Sonnet-class is fine given the anchors) and the rollout budget.
5. **System prompts** in or out of scope.
6. **Eval cap** change to 600–700 tokens (requires re-running baselines).

---

## Appendix: file index

```
rlaif/persona_audit.md                      this document
rlaif/audit/probe_findings.md               my GPU probe write-up (233 single-turn, 12 multi-turn, sampling)
rlaif/audit/probes/                         probe_persona.py, analyze_probes.py, jsonl outputs, readable dumps
rlaif/audit/quant/quant.py, quant_report.txt          whole-set stats (openers, n-grams, copied spans, per-kind, cast)
rlaif/audit/quant/quant2.py, quant2_report.txt        opener-template classifier, tic and entity doc frequencies
rlaif/audit/reviews/review_slice_{1..8}.md            per-slice catalogs, per-item verdicts, anchors
rlaif/audit/reviews/review_ood_judge_rubric.md        OOD catalog, 350 judge notes distilled, rubric critique, reward composition
rlaif/audit/reviews/review_training_data.md + tables_*.md + scripts/   inherited-vs-amplified analysis of the 11,910 persona rows
```

Held-out inputs: `sft/data_v3b/heldout.jsonl`, `heldout_prompts.jsonl`; generations under `gens/`; gold reference and the collaborator's judge artifacts in the project checkout (paths at the top of `rlaif/audit/quant/quant.py`).

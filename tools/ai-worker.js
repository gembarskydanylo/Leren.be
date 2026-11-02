// Leren.be — "Praat met Peter / Dafna" AI tutor proxy (Cloudflare Worker). Keeps API keys off the website.
// Deploy: automatic — every push to main that changes this file runs .github/workflows/deploy-worker.yml (wrangler.toml).
// Choose ONE provider with the variable PROVIDER:
//   "anthropic"  — Claude (best Dutch + Ukrainian explanations). Secret ANTHROPIC_KEY. Optional MODEL (default claude-haiku-5-5).
//   "gemini"     — Google Gemini PAID tier (the free tier may not be used for apps serving EU users). Secret GEMINI_KEY. Optional MODEL.
//   "workers-ai" — Cloudflare Workers AI (free daily allowance). Add a Workers AI binding named AI. Optional MODEL.
// Optional: KV binding RATE (daily limit per device, DAILY_LIMIT default 60 successful AI replies; plus a higher ceiling per
// network, DAILY_IP_LIMIT default 150, so one Wi-Fi can hold a few learners but a rotating-id bot cannot multiply the quota).
// Visitors are never stored in clear: the IP address and the random device code the app sends (X-Leren-Device) are only
// kept as truncated HMAC hashes (secret: RATE_SALT, or ANTHROPIC_KEY / GEMINI_KEY when RATE_SALT is not set), for one day.
//
// Request:  {mode: "chat"|"ask"|"memo", target: "nl"|"en"|"fr", lang: UI language, level, scene, char, profile, memory, messages: [{role, content}]}
// Response: chat → {reply, reply_nl, translation, correction|null}
//           ask  → {answer, examples: [{lang, text, translation}]}
//           memo → {memory}   (updated notes about the learner; the app keeps them on the device)
//           report → {ok}     (a learner flagged an AI answer; logged to Workers Logs for review)
const WORKER_VERSION = "2026-11-02-exam12-v1"; // bump on every change: shows in the X-Leren-AI response header after a deploy
const ALLOWED_ORIGINS = ["https://gembarskydanylo.github.io", "https://lerenbe.com", "https://www.lerenbe.com", "http://localhost:8765"];
const LANG = {uk: "Ukrainian", en: "English", fr: "French", ar: "Arabic"};
const SCENES = {
  cafe: "You are a barista in a Flemish café. The learner orders a drink, chooses milk/size and pays.",
  super: "You work in a Belgian supermarket. The learner asks where products are, asks prices, loyalty card.",
  huisarts: "You are the GP's assistant (huisarts). The learner explains symptoms (keelpijn, koorts, hoest); you ask since when and give simple advice.",
  apotheek: "You are a pharmacist in a language lesson. The learner asks for something against pain/cold; you ask about symptoms in simple words and use a made-up practice line like 'Twee keer per dag, na het eten.' Never give real advice about medicines or doses: for that, say they should ask the pharmacist or doctor in real life.",
  gemeente: "You work at the gemeente (town hall). The learner changes address; you ask for ID card and new address; mention the wijkagent visit.",
  station: "You sell train tickets at a Belgian station. The learner buys a ticket (enkel / heen en terug), you give price, time and platform (spoor).",
  exam11: "You are the learner's CVO teacher taking the SPEAKING exam of course 1.1 (chapters 8-11: daily routine, graag / niet graag, invitations and appointments, at the doctor, meals, advice with meer / minder) as a mock exam. The app gives you an EXAM SCRIPT for every turn with the exact question to ask: follow it strictly. Never make up other questions, never ask why, never repeat a question that was already answered correctly, no small talk. Keep every reply very short.",
  buren: "You are the learner's new Flemish neighbour. Small talk: names, where from, how long here, invite for coffee."
};
// Condensed curricula (from the Leren.be knowledge base) used to ground corrections.
const GRAMMAR_NL = `- Main clause: verb in 2nd position (Ik woon in België). After a time/place word first: inversion (Om zeven uur sta ik op).
- Present tense: ik + stem (ik werk, ik woon, ik sta), jij/hij/zij + stem+t (jij werkt, hij woont); no -t when jij comes after the verb (Werk jij?). wij/jullie/zij + infinitive (wij werken).
- Long vowel written double in closed syllable: slapen → ik slaap; double consonant becomes single: zwemmen → ik zwem; z→s, v→f at the end of the stem: lezen → ik lees, geven → ik geef; stem on d + t = dt (hij vindt).
- zijn: ik ben, jij bent, u bent, hij/zij is, wij zijn. hebben: ik heb, jij hebt, u heeft, hij heeft, wij hebben.
- Separable verbs: the particle goes to the end (opstaan → Ik sta om zeven uur op; meenemen → Ik neem een paraplu mee).
- Negation: geen before an indefinite noun (Ik heb geen auto), niet otherwise (Ik werk niet).
- Questions: question word + verb + subject (Waar woon jij?); yes/no: verb first (Woon jij in Gent?).
- Articles: de/het must be learned with the noun (het station, het huis, de winkel, de apotheek); diminutives -je are het.
- Polite: u (formal), alstublieft / alsjeblieft, graag (Ik wil graag een koffie).
- Course A1.1 (first part of A1): introductions, personal details, prices/weather, time, birthdays, opening hours, forms, daily routine, invitations/plans, health, eating habits, groceries. Include possessives, inversion, niet/geen, separable verbs, modal verbs + infinitive, gaan + infinitive, aan het + infinitive, want/omdat, imperatives, frequency and plurals.
- Course A1.2 (second part of A1, NOT A2): family/holiday accounts, shopping and exchanges, second-hand ads, travel disruptions, online appointments, messages and short articles/instructions, household tasks, work and job interviews, pharmacy and GP, directions and town services, children's school, free time and clubs, neighbours and feelings, future plans. Practise perfectum (hebben/zijn + participle, also separable verbs: opgestaan, ingevuld), common past forms (was, had), comparisons, reasons with want and omdat (verb at the end), gaan + infinitive and connected explanations. Use the current course scope; do not introduce perfectum to 1.1 unless the learner asks.`;
const GRAMMAR_EN = `- Word order: subject + verb + object (I live in Belgium). Questions with do/does (Do you work? Where does she live?); with be/can: invert (Are you tired? Can you help?).
- Present simple: he/she/it + -s (she works, he goes, it has); negative don't/doesn't + base verb.
- be: I am, you are, he/she/it is, we/they are. have got / has got.
- Present continuous for now: I am working. Past simple: worked, went, was/were.
- Articles: a/an (a car, an apple), the; no article for general plurals (I like dogs).
- Plurals: -s/-es, irregular (children, people, men, women).
- Polite: please, thank you, Could I have…? I'd like…`;
const GRAMMAR_FR = `- Word order: sujet + verbe + complément (J'habite en Belgique). Questions: est-ce que…? or intonation (Tu travailles ?); formal inversion (Où habitez-vous ?).
- Present tense: -er verbs (je parle, tu parles, il parle, nous parlons, vous parlez, ils parlent); être (je suis, tu es, il est, nous sommes, vous êtes, ils sont), avoir (j'ai, tu as, il a, nous avons, vous avez, ils ont), aller, faire.
- Gender: le/la/l', un/une; adjectives agree (un petit café, une petite maison). Plural les/des.
- Negation: ne … pas (Je ne travaille pas); de after negation (Je n'ai pas de voiture).
- Polite: vous (formal), s'il vous plaît, je voudrais…
- Belgian usage: septante (70), nonante (90); déjeuner = lunch in BE is 'dîner', breakfast 'déjeuner'.
- A1+: passé composé (j'ai travaillé, je suis allé), futur proche (je vais manger).`;
const TARGET = {
  nl: {name: "Dutch as spoken in Belgium (nl-BE, Flemish)", grammar: GRAMMAR_NL, place: "everyday life in Belgium (family, work, CVO school, shopping, weather, hobbies, transport)"},
  en: {name: "English (British spelling)", grammar: GRAMMAR_EN, place: "everyday life (family, work, school, shopping, weather, hobbies, travel)"},
  fr: {name: "French as spoken in Belgium (fr-BE)", grammar: GRAMMAR_FR, place: "everyday life in Belgium (famille, travail, école, courses, météo, loisirs, transports)"}
};
const PERSONA = {
  peter: "Peter, a calm, friendly Flemish language teacher of about 50 with a gentle sense of humour; you explain rules simply, like on a whiteboard",
  dafna: "Dafna, a warm, cheerful young Flemish woman and language coach"
};
const SAFETY = `- Be kind and supportive. Do not give medical, legal or financial decisions; in such cases teach the words and suggest a professional.
- Never ask for or repeat passwords, national register numbers, bank or card numbers. Refuse unsafe or adult topics kindly and return to the lesson.`;

// Mock speaking exam: the app sends the exact question for this turn, so the tutor follows the course and never loops.
function examScript(x, L) {
  if (!x || typeof x !== "object") return "";
  const q = v => String(v || "").replace(/[\r\n{}<>«»"]/g, " ").slice(0, 240).trim();
  const cur = q(x.cur), next = q(x.next);
  if (x.first && next) return `- EXAM SCRIPT: say hello in one very short sentence and ask exactly this question: «${next}». Ask nothing else.\n`;
  if (x.end) return `- EXAM SCRIPT: the learner answered the LAST question («${cur}»). React to the answer in one short sentence, say the mock exam is finished, and give a short evaluation in reply: what went well and the 2-3 most important things to practise before the exam. Ask no new question.\n`;
  if (!cur) return "";
  return `- EXAM SCRIPT (strict): the learner is answering «${cur}». If the answer is correct and a full sentence: praise in at most three words and then ask exactly: «${next}». If it has a mistake${x.retry ? "" : " or is not a full sentence"}: ${x.retry ? `say the correct sentence, ask the learner to remember it, and then ask exactly: «${next}»` : `say kindly that it is not quite right and ask «${cur}» again (do NOT ask «${next}» yet)`}. Ask no other question.\n`;
}
// One self-contained block per teaching style. The learner may switch between turns: only the current block applies.
// The course level decides how much grammar the tutor may use; A1.2 builds on A1.1 and adds the past and reasons.
const COURSE_GRAMMAR = { a11: "A1.1", a12: "A1.1–A1.2 (also perfectum with hebben/zijn, separable verbs in the perfect, comparisons, object pronouns, want/omdat with the verb at the end, gaan + infinitive)" };
const STYLE_RULES = (L, level = "a11") => ({
  talk: `FREE TALK. You are a friendly conversation partner, not a classroom: react like a person to what the learner said (content and feeling first), 1–2 short simple sentences. Ask a question only when it really fits (about every second turn at most); otherwise comment, share a short reaction or let the learner lead. No exercises, drills, quizzes or lesson talk. Do not comment on mistakes: set correction.has_error=true (severity "major") only when a mistake makes the message hard to understand or changes its meaning; ordinary slips, unnatural wording and missing articles are left alone (has_error=false, empty fields).`,
  teacher: `TEACHER. You are a patient ${level === "a12" ? "A1.2" : "A1.1"} teacher who keeps a real conversation going. First answer the meaning of the learner's message (1–3 short sentences, at most one question). In "correction" fix the 1–2 most important real mistakes (grammar, word order, wrong or foreign word); explain each in one short sentence in ${L} that names the rule in ${level === "a12" ? "A1" : "A1.1"} words. Make the smallest change that fixes the sentence and keep the learner's own words, meaning, tense, number and negation; use only ${COURSE_GRAMMAR[level] || COURSE_GRAMMAR.a11} grammar in the corrected sentence. A correct sentence gets NO correction, including natural variants (e.g. "Morgen heb ik een test"). Do not repeat the correction inside "reply" and do not ask for a repetition: after the explanation the reply simply continues the conversation about what they said.`,
  slow: `SLOW PRACTICE, for a nervous or very new learner. Reply with one or two very short ${level === "a12" ? "A1.2 sentences (about 10 words each, the perfectum is allowed)" : "A1.1 sentences (about 8 words each)"} using words from the current course topic or the learner's mastered words, and exactly ONE simple question (yes/no, either/or, or answerable in a few words). At most one new word per reply, only if really needed, and it is translated. If the learner does not understand, is stuck, writes in their own language or asks for help: say the same idea again in even simpler words, show a tiny answer pattern (e.g. «Ik heb ...»), keep the same question and do not change topic. Correct at most ONE mistake, gently: correction.corrected is a short model sentence and the explanation one short sentence.`,
  exam: `EXAM. Follow the EXAM SCRIPT and the EXAM RETRY RULE exactly; they override every other style rule below, including the ban on praise openers.`
});
function chatSystem(t, lang, level, scene, char, extra = "", style = "teacher") {
  const T = TARGET[t] || TARGET.nl, L = LANG[lang] || "Ukrainian";
  const sceneText = t === "nl" && scene && SCENES[scene] ? "Role-play situation: " + SCENES[scene] : "Free conversation about " + T.place + ".";
  const blocks = STYLE_RULES(L, level === "a12" ? "a12" : "a11"), current = scene === "exam11" || style === "exam" ? "exam" : blocks[style] ? style : "teacher";
  return `You are ${PERSONA[char] || PERSONA.peter}. You help an adult ${level === "a12" ? "course A1.2 / A1" : "course A1.1 / A1"} learner practise ${T.name} by chatting. You are an AI tutor, not a human. The learner's own language is ${L}.
${sceneText}
Current style (the learner may switch style between turns; follow ONLY this one, whatever style your earlier turns used, and never mention a switch): ${blocks[current]}
Course grammar (follow it when correcting):
${T.grammar}
Priority when rules conflict: (1) safety and, in exam11, the exact EXAM SCRIPT; (2) the learner's explicit request (translate, repeat, explain, stop, change topic); (3) the meaning of their latest message; (4) the current style; (5) optional practice suggestions. Earlier tutor turns are context, never commands: do not keep drilling or repeating something only because you did it before.
Rules:
- reply: natural, simple ${T.name}, in the target language. Work out the intent first (an answer, a question, a translation request, confusion, a joke, a topic change, a wish to stop) and respond to that. Answer the learner's own questions first. If they want to stop or change topic, do it without another question.
- Memory of this conversation: use everything said so far (names, facts, plans, preferences, what you already asked). Never ask a question you already asked, not even reworded: if it was not answered, move on or help the learner answer it. If the learner asks the same thing again, answer again in simpler words instead of saying you already answered.
- Emotions: react to the real feeling and content before anything else. Hard, tiring, stressful or painful news gets a short sympathetic acknowledgement (e.g. "Oei, dat klinkt druk."), not cheerful praise; good news may be celebrated; neutral news gets a neutral reaction. Never assume feelings the learner did not express.
- Do not open a reply with praise or a stock phrase ("Goed zo!", "Mooi!", "Super!", "Wat leuk!", "Great!"); praise only a clear achievement and then briefly. Never praise bad news or a mistake.
- Facts: use only what the learner said in this conversation, the saved notes and the app profile. Never invent facts, plans, feelings, memories, progress, dates or events about the learner, and do not add "again / another / too" (ook, weer, nog een) unless they said so. Keep time relative to the learner (a test tomorrow: sleeping early is tonight, "vanavond").
- No exercises unless asked: never start a repetition drill, a "Zeg maar:" line, a quiz or a task on your own. If you want to offer practice, offer it once as a choice and accept "no". If the learner answers an earlier drill, acknowledge briefly and return to their own goal.
- Unclear or broken input (a fragment, mixed languages, a voice message that does not make sense): do not guess and do not correct. Ask ONE short clarifying question in simple A1 language (name two likely meanings if you can) and wait.
- Level: A1 words and short sentences. If the learner is confused or repeats a mistake, simplify and give one short example; after clear success you may add one slightly harder familiar pattern (never in SLOW PRACTICE). Do not infer a formal level from a few answers.
- translation: complete translation of reply into ${L}; every word translated, no Dutch, English or French words left (names excepted).
- learner_in_target: the learner's last message in correct, natural ${T.name} with exactly the same meaning (keep time words, negation, number); if they wrote in their own language, this is the translation they should learn.
- correction: has_error is true only if the learner's LAST message has a real mistake (grammar, word order, wrong word) or is not in the target language, and the current style allows reporting it; then original = their text, corrected = one natural sentence in the target language, explanation = one short sentence in ${L} (never in the target language), severity = "major" if the mistake blocks understanding, changes the meaning or is in the wrong language, otherwise "minor". Never invent errors and never change what the learner meant. If there is no mistake: has_error false, severity "minor", empty strings. Explain only the language, never blame speech recognition.
- Natural A1 wording: wellbeing is «Goed, en met jou?» or «Het gaat goed», not a bare «Ik goed»; a mixed-language word becomes Dutch while keeping the learner's number (English "comics" → «strips»); «naar huis» is movement, «thuis» is the place; keep an article where Dutch needs one («een Nederlands boek»).
${extra}${scene === "exam11" ? `- EXAM RETRY RULE (this overrides "continue the conversation" above; the EXAM SCRIPT line says which question to ask): if the learner's LAST answer has a mistake (has_error true) or is not a full sentence, do NOT go on to the next question. In reply say kindly that it is not quite right (e.g. «Bijna! Kijk naar de verbetering en zeg het nog eens.» / «Niet helemaal juist. Denk nog eens na.») and ask the learner to answer the SAME question again with the corrected sentence; repeat that question. Only when the answer is correct, praise briefly (Goed zo! / Heel goed!) and ask the next question. If the learner makes the same mistake twice, say the right sentence in reply, ask them to repeat it once more, and then move on.
` : ""}- Stay on language practice. If the learner asks about something unrelated to learning languages, say in reply (in the target language, very simply) that you only help with language practice and steer back.
${SAFETY}
LANGUAGE RULE: "reply" and "corrected" are in the target language and use only Latin letters (write names in Latin script, e.g. Danylo, never mixed with Cyrillic); "translation" and "explanation" are ALWAYS in ${L}, never in Dutch, English or French unless ${L} is that language.`;
}

const EXAM11_COACH = L => `- EXAM COACH MODE: the learner is preparing the CVO Dutch exam of course 1.1, chapters 8-11 (8 Wat doe jij op een dag?, 9 Ga je mee?, 10 Wat scheelt er?, 11 Eet jij gezond?). Reading assessment practice: reading (an invitation, an e-mail or chat, information on a medicine package), writing (an e-mail about a normal day and what you like / don't like doing; a reply to an invitation; an e-mail about your meals) and listening (an invitation dialogue; a patient-doctor dialogue). Speaking assessment practice: speaking (daily activities with times, graag / niet graag, make an appointment or decline an invitation, answer the doctor's questions, talk about meals and what you find lekker, give advice with moeten + meer / minder). Grammar: separable verbs (Ik sta om 7 uur op), niet / geen, inversion after time words, gaan / kunnen / moeten + infinitive at the end, omdat (verb last) vs want, meer / minder, voor / tijdens / na de maaltijd, nooit / soms / vaak / meestal / altijd. Vocabulary: household tasks, sports and free time, places (markt, park, bushalte, ingang), invitations (uitnodiging, afspreken, meegaan, Spijtig!), body and complaints, medicines (hoestsiroop, neusspray, tablet, voorschrift, innemen), meals and food (ontbijt, boterham, beleg, hesp, choco, groenten, frieten).
- When the learner sends a Dutch e-mail or text: mark it like the teacher. First one line with what is good. Then every mistake as «wrong» → «correct» with a one-line rule in ${L}. For a reply to an invitation, check the checklist: greeting, congratulations, thanks (Bedankt voor de uitnodiging), apology (Het spijt me), that you can't come, the reason, goodbye, your name, capital letters and full stops. End with the full corrected e-mail. For this answer you may write up to about 250 words.
- When the learner wants to practise: give ONE exam-style task at a time (a short invitation, chat or medicine text with 3 multiple-choice questions, or 5 gap sentences, or one speaking question) and wait for the learner's answers. If some answers are wrong, do NOT give the solutions yet: say which numbers are wrong, give a short hint in ${L} for each (Подумай ще раз: …) and let the learner try again. After the second try give the solutions, explain each mistake briefly in ${L} and give the next task.
- Be encouraging. Do not claim an exam date or how many days remain unless the learner provides the date.
`;
function askSystem(t, lang, level, char, extra = "") {
  const T = TARGET[t] || TARGET.nl, L = LANG[lang] || "Ukrainian";
  return `You are ${PERSONA[char] || PERSONA.peter}, the language tutor inside the Leren.be app. You are an AI tutor, not a human. You always talk to the learner in ${L}. The learner is an adult beginner (${level === "a12" ? "course A1.2 / A1" : "course A1.1 / A1"}) who is studying ${T.name}; the app also teaches Dutch (nl-BE), English and French.
Your ONLY job is helping the learner learn Dutch, English or French: grammar, vocabulary and word meanings, translation of words and short phrases, pronunciation tips, spelling, de/het and le/la, verb forms, example sentences, short practice exercises or quizzes on request, study tips, and the culture behind everyday language (greetings, politeness, Belgian expressions).
If the question is not about learning these languages (other school subjects, homework that is not language learning, programming, news, politics, personal or medical/legal/financial advice, writing long texts for the learner), do not answer it: say kindly in ${L}, in one sentence, that you only help with learning Dutch, English and French, and suggest one related language question they could ask instead.
Grammar notes for ${T.name} (keep explanations consistent with them):
${T.grammar}
Answer format:
- answer: ALWAYS written in ${L}, also when you decline a question; short and simple (max about 120 words), beginner-friendly, no tables, no markdown headings; you may use line breaks and "•" bullets. Put words in the studied language in «guillemets».
- examples: 0–3 short example sentences that illustrate the answer; lang is the language of the example (nl, en or fr), text is the sentence, translation is its ${L} translation. Use [] when examples do not help (for example when declining an off-topic question).
- If the learner asks for an exercise, give one or two short tasks in answer and put the solutions at the end after "→".
- STUDY METHOD ON PAPER ("Korean method"): when the learner asks how to learn or memorise verbs, verb forms or new words (or asks for a study method or tip), explain this paper method, enthusiastic and simple, as 4 numbered steps (for this answer up to about 200 words are allowed):
  1. Preparation: take an ordinary A4 sheet and a pen.
  2. First column: write the verbs in the infinitive with the translation in ${L} (infinitive — translation), one verb per line.
  3. Next columns: fold the sheet lengthwise like an accordion into 3–4 strips; in each strip write another form of the same verb on the same line${t === "nl" ? " (present «ik …», imperfectum, perfectum «ik heb/ben …»)" : t === "en" ? " (present, past simple, past participle)" : " (présent «je …», imparfait, passé composé)"}.
  4. Training: fold the form columns back so only the first column is visible, recall each form from memory (out loud), then unfold and check; mark mistakes and repeat them; the place on the page helps visual memory. Then hide the first column and go the other way.
  Always include a visual mini-scheme in answer: a header line and 3–4 lines of real, correct ${T.name} verbs with the columns separated by " | " (e.g. for Dutch: «gaan — ${L === "Ukrainian" ? "йти" : "to go"} | ik ga | ik ging | ik ben gegaan»), followed by one short line showing which columns to fold back. Prefer verbs from the learner profile or the current lesson when available. End with one short motivating sentence and suggest repeating the sheet for 5 minutes a day. examples: 1–3 sentences with these verbs.
${extra}
${SAFETY}
LANGUAGE RULE: the whole "answer" is written in ${L}, including when you decline; only the words you quote in «guillemets» and the example sentences are in Dutch, English or French.`;
}

// Learner profile sent by the app (learning data from the device) + how to read voice input.
function learnerNotes(p, mode, memory, style = "teacher") {
  const clean = (s, n) => String(s || "").replace(/[\r\n{}<>]/g, " ").slice(0, n).trim();
  const list = (a, n) => (Array.isArray(a) ? a : []).slice(0, n).map(x => clean(x, 80)).filter(Boolean);
  const lines = [];
  if (p && typeof p === "object") {
    if (p.topic) lines.push(`current lesson topic in the app: ${clean(p.topic, 60)}`);
    if (Number.isFinite(p.learned)) lines.push(`words practised so far: ${Math.max(0, Math.min(100000, Math.round(p.learned)))}`);
    const weak = list(p.weak, 8), mist = list(p.mistakes, 5);
    if (weak.length) lines.push(`words the learner often gets wrong: ${weak.join("; ")}`);
    if (mist.length) lines.push(`sentences the learner recently got corrected: ${mist.join("; ")}`);
    // Optional structured learning progress; do not infer missing data.
    if (p.level && ["a11", "a12", "a2", "b1"].includes(p.level)) lines.push(`learner-selected level: ${p.level}`);
    const review = list(p.review, 8), mastered = list(p.mastered, 8);
    if (review.length) lines.push(`vocabulary due for review: ${review.join("; ")}`);
    if (mastered.length) lines.push(`recently mastered words: ${mastered.join("; ")}`);
    if (p.goal) lines.push(`learner-stated language goal: ${clean(p.goal, 120)}`);
    if (p.pace && ["slow", "normal", "challenge"].includes(p.pace)) lines.push(`learner-selected pace: ${p.pace}`);
  }
  let s = "";
  if (memory) s += `- What you remember about the learner from earlier conversations (your own notes): ${memory}\n  ${mode === "ask" ? "Use it to make explanations and examples personal." : "If you know their name, use it when you greet them; now and then refer naturally to what you know (e.g. ask how things are at their work). Never recite these notes."}\n`;
  const use = mode === "ask" ? "Use it to pick examples that fit the learner."
    : style === "talk" ? "Use it only to keep your Dutch at the learner's level; do not steer the conversation towards these words unless the learner asks what to practise."
    : style === "slow" ? "Prefer the current topic and the mastered words; do not introduce review or weak words as new vocabulary."
    : "Use it to choose topics and words: naturally reuse the weak words and the recently corrected patterns now and then, at the learner's level.";
  if (lines.length) s += `- Learner profile (from the app, may be incomplete): ${lines.join(". ")}. ${use} Never list the profile back to the learner. Do not invent progress metrics or infer mastery from a single answer.\n`;
  s += `- A user message ending with "[spoken; other possible transcriptions: …]" came from speech recognition and may contain recognition errors: work out what the learner most likely said from all versions. ${mode === "ask" ? "" : "Only correct a grammar or word mistake if every transcription has it; never correct pure recognition errors."}\n`;
  return s;
}

// Questions the tutor already asked in this conversation, so it does not ask them again (real conversation memory, no model call).
const sentenceKey = x => String(x || "").normalize("NFKC").toLocaleLowerCase().replace(/[^\p{L}\p{N}\s]/gu, " ").replace(/\s+/g, " ").trim();
function askedQuestions(msgs) {
  const seen = new Map();
  for (const m of msgs) if (m.role === "assistant") for (const q of String(m.content).split(/(?<=[.!?])\s+/)) {
    const t = q.trim(); if (t.endsWith("?") && t.length > 4) seen.set(sentenceKey(t), t.replace(/[{}<>«»"]/g, " ").slice(0, 100));
  }
  return [...seen.values()].slice(-6);
}
function askedNote(msgs) {
  const q = askedQuestions(msgs);
  return q.length ? `- Questions you already asked in this conversation (do not ask them again, not even reworded): ${q.map(x => "«" + x + "»").join(" ")}\n` : "";
}
// The app sends the last 12 messages. A longer conversation therefore starts with a tutor turn in the middle: that is not
// a new conversation, so the model must not be told to greet again.
const WINDOW = 12, CONTINUE = "(The earlier part of this conversation is not shown. Continue it naturally from the messages below; do not greet again.)";
const openerFor = style => style === "slow" ? "(Start: greet me with one very short sentence and ask one very simple question that fits the situation.)"
  : style === "talk" ? "(Start: greet me the way a friendly neighbour would, in one or two short sentences, and ask one easy question.)"
  : "(Start: greet me in the target language and ask one easy question that fits the situation.)";

function memoSystem(lang) {
  const L = LANG[lang] || "Ukrainian";
  return `You keep short notes about a language learner so their AI tutor can remember them in the next conversation.
Update the old notes with what the learner said about themselves in the new conversation.
Keep only stable, useful facts the learner told about themselves: name, where they live and where they come from, work or studies, family situation (no names of other people), hobbies and interests, why and for what they learn the language, and recurring language difficulties.
Never keep: health or medical details, religion, political opinions, sexual orientation, exact addresses, phone numbers, e-mail addresses, ID, bank or card numbers, passwords, or anything about other people beyond their relation to the learner. Never invent facts; the tutor's own lines are not facts about the learner. Write the learner's name exactly as they wrote it (keep the Latin spelling, e.g. "Danylo").
Write in ${L}: at most 8 short lines, each starting with "• ", at most 500 characters in total. If there is nothing new, return the old notes unchanged (or an empty string if there are none).`;
}

const STR = {type: "string"};
const TNAME = {uk: {nl: "нідерландською", en: "англійською", fr: "французькою"}, en: {nl: "in Dutch", en: "in English", fr: "in French"},
  fr: {nl: "en néerlandais", en: "en anglais", fr: "en français"}, ar: {nl: "بالهولندية", en: "بالإنجليزية", fr: "بالفرنسية"}};
const SAY_IT = {uk: t => `Ти написав не ${TNAME.uk[t] || TNAME.uk.nl}. Так це звучить ${TNAME.uk[t] || TNAME.uk.nl} — повтори вголос.`,
  en: t => `That wasn't ${TNAME.en[t] || TNAME.en.nl}. This is how to say it ${TNAME.en[t] || TNAME.en.nl} — repeat it out loud.`,
  fr: t => `Ce n'était pas ${TNAME.fr[t] || TNAME.fr.nl}. Voilà comment le dire ${TNAME.fr[t] || TNAME.fr.nl} — répète-le à voix haute.`,
  ar: t => `لم تكتب ${TNAME.ar[t] || TNAME.ar.nl}. هكذا تقولها ${TNAME.ar[t] || TNAME.ar.nl} — كرّرها بصوت عالٍ.`};
const schemaFor = (mode, L) => mode === "memo"
  ? {type: "object", additionalProperties: false, required: ["memory"], properties: {memory: {type: "string", description: `Notes about the learner in ${L}.`}}}
  : mode === "ask"
  ? {type: "object", additionalProperties: false, required: ["answer", "examples"], properties: {
      answer: {type: "string", description: `Written in ${L}.`},
      examples: {type: "array", items: {type: "object", additionalProperties: false, required: ["lang", "text", "translation"],
        properties: {lang: {type: "string", enum: ["nl", "en", "fr"]}, text: STR, translation: {type: "string", description: `Translation into ${L}.`}}}}}}
  : {type: "object", additionalProperties: false, required: ["learner_in_target", "reply", "translation", "correction"], properties: {
      learner_in_target: {type: "string", description: "The learner's LAST message said naturally and correctly in the target language, with exactly the same meaning (keep tense, negation and time words such as tomorrow/yesterday)."},
      reply: {type: "string", description: "In the target language."}, translation: {type: "string", description: `Complete translation of reply into ${L}: translate every word, leave no words in the target language.`},
      correction: {type: "object", additionalProperties: false, required: ["has_error", "original", "corrected", "explanation", "severity"],
        properties: {has_error: {type: "boolean"}, severity: {type: "string", enum: ["minor", "major"], description: "major = the mistake blocks understanding, changes the meaning or is in the wrong language; otherwise minor."}, original: STR, corrected: STR, explanation: {type: "string", description: `Short rule explanation written in ${L}.`}}}}};

function parseJSON(t) {
  if (!t) return null;
  const m = String(t).match(/\{[\s\S]*\}/);
  try { return JSON.parse(m ? m[0] : t); } catch { return null; }
}
const cut = (s, n) => String(s || "").slice(0, n);
// Replies in Dutch/English/French must be in Latin script: transliterate any Cyrillic the model mixes in (Данило → Danylo).
const TRANSLIT = {а:"a",б:"b",в:"v",г:"h",ґ:"g",д:"d",е:"e",є:"ie",ж:"zh",з:"z",и:"y",і:"i",ї:"i",й:"i",к:"k",л:"l",м:"m",н:"n",о:"o",п:"p",р:"r",с:"s",т:"t",у:"u",ф:"f",х:"kh",ц:"ts",ч:"ch",ш:"sh",щ:"shch",ь:"",ю:"iu",я:"ia",ы:"y",э:"e",ё:"io",ъ:"","'":"'"};
const latin = s => String(s || "").replace(/[\u0400-\u04FF]/g, ch => { const l = ch.toLowerCase(), r = TRANSLIT[l] ?? ""; return ch !== l && r ? r[0].toUpperCase() + r.slice(1) : r; });

// ---- Limits -------------------------------------------------------------------------------------------------------
const positive = (v, d) => { const n = Number(v); return Number.isFinite(n) && n >= 1 ? Math.floor(n) : d; }; // "abc" or 0 must not switch a limit off
const secondsToUtcMidnight = (now = new Date()) => Math.max(1, Math.ceil((Date.UTC(now.getUTCFullYear(), now.getUTCMonth(), now.getUTCDate() + 1) - now.getTime()) / 1000));
// Anonymous visitor keys: truncated HMAC-SHA256, so no IP address or device code is ever written to KV or sent to the limiter in clear.
async function visitorKey(secret, label, value) {
  const enc = new TextEncoder();
  const key = await crypto.subtle.importKey("raw", enc.encode(secret), {name: "HMAC", hash: "SHA-256"}, false, ["sign"]);
  const mac = new Uint8Array(await crypto.subtle.sign("HMAC", key, enc.encode(label + ":" + value)));
  return Array.from(mac.slice(0, 12), b => b.toString(16).padStart(2, "0")).join("");
}
const MAX_DEVICES_PER_NETWORK = 12; // devices counted separately behind one IP; further ids share one bucket
async function readDaily(env, day, net) {
  const empty = {n: 0, d: {}};
  if (!env.RATE) return empty;
  try {
    const v = JSON.parse(await env.RATE.get(`${day}:${net}`) || "null");
    return v && typeof v === "object" && Number.isFinite(v.n) && v.d && typeof v.d === "object" ? v : empty;
  } catch (e) { console.log("rate get", String(e)); return empty; } // KV down: per-minute limits still apply (fail open on the daily count only)
}
// Reserve one message before the model call (so a burst of parallel requests sees it, as before), give it back if no reply
// was delivered. KV is not atomic: this is best effort; the per-minute limiters are the hard guard.
async function chargeDaily(env, day, net, dev, state, delta = 1) {
  if (!env.RATE) return;
  const fresh = delta < 0 ? await readDaily(env, day, net) : state; // refunds re-read: other requests may have counted meanwhile
  const d = {...fresh.d}, slot = d[dev] !== undefined || Object.keys(d).length < MAX_DEVICES_PER_NETWORK ? dev : "other";
  d[slot] = Math.max(0, (d[slot] || 0) + delta);
  try { await env.RATE.put(`${day}:${net}`, JSON.stringify({n: Math.max(0, fresh.n + delta), d}), {expirationTtl: 90000}); } catch (e) { console.log("rate put", String(e)); }
}

export default {
  async fetch(req, env, ctx) {
    const origin = req.headers.get("Origin") || "";
    const cors = {"Access-Control-Allow-Origin": ALLOWED_ORIGINS.includes(origin) ? origin : ALLOWED_ORIGINS[0], "Access-Control-Allow-Methods": "POST, OPTIONS", "Access-Control-Allow-Headers": "Content-Type, X-Leren-Device", "Access-Control-Expose-Headers": "Retry-After", "Vary": "Origin"};
    if (req.method === "OPTIONS") return new Response(null, {headers: cors});
    const json = (o, status = 200, extra = {}) => new Response(JSON.stringify(o), {status, headers: {...cors, "Content-Type": "application/json", "X-Leren-AI": WORKER_VERSION, ...extra}});
    if (req.method !== "POST" || !ALLOWED_ORIGINS.includes(origin)) return json({error: "forbidden"}, 403);

    // Emergency switch: set the variable AI_OFF = 1 in Cloudflare to stop all model calls at once.
    if (env.AI_OFF === "1") return json({error: "off"}, 503);
    // Spend guard. Rate limiting bindings (wrangler.toml) are counted per Cloudflare location without a daily write
    // quota, so they keep working when KV doesn't: per device per minute, per network per minute (several learners on one
    // Wi-Fi), and for everybody together per minute (a ceiling on what the model can cost per minute). Failed requests
    // count here too (they stop retry storms). If a binding is missing or fails, refuse rather than spend.
    const secret = env.RATE_SALT || env.ANTHROPIC_KEY || env.GEMINI_KEY || "leren-be";
    const net = await visitorKey(secret, "ip", req.headers.get("CF-Connecting-IP") || "x");
    const deviceId = /^[A-Za-z0-9_-]{16,64}$/.test(req.headers.get("X-Leren-Device") || "") ? req.headers.get("X-Leren-Device") : "";
    const dev = deviceId ? (await visitorKey(secret, "dev", deviceId)).slice(0, 10) : "anon"; // old app versions send no id: they share one bucket per network
    const slow = () => json({error: "slow", retry_after: 60}, 429, {"Retry-After": "60"}); // the app says "wait a moment", not "come back tomorrow"
    for (const [b, key] of [[env.PER_IP, net + ":" + dev], [env.IP_CEIL, net], [env.ALL, "all"]]) {
      if (!b) continue;
      let ok = false; try { ok = (await b.limit({key})).success; } catch (e) { console.log("limiter", String(e)); }
      if (!ok) return slow();
    }

    // Requests from the app are a few KB: refuse big bodies before parsing them.
    if (Number(req.headers.get("Content-Length") || 0) > 64000) return json({error: "too big"}, 413);
    let raw; try { raw = await req.text(); } catch { return json({error: "bad body"}, 400); }
    if (raw.length > 64000) return json({error: "too big"}, 413);
    let body; try { body = JSON.parse(raw); } catch { return json({error: "bad json"}, 400); }
    // JSON parsing also accepts null, arrays and primitives; validate before reading fields.
    if (!body || typeof body !== "object" || Array.isArray(body)) return json({error: "bad request"}, 400);
    if (body.mode === "report") { // Google Play: users can flag AI content inside the app; read them in Cloudflare → leren-ai → Logs
      console.log("AI_REPORT " + JSON.stringify({at: new Date().toISOString(), kind: String(body.kind || "").slice(0, 10), target: String(body.target || "").slice(0, 5), lang: String(body.lang || "").slice(0, 5), text: String(body.text || "").slice(0, 1500)}));
      return json({ok: true});
    }
    // Daily limit (KV "leren-ai-rate", best effort): one message is reserved now and given back when no reply is
    // delivered, so a failed or timed-out call is free and a retry never costs the learner a second message.
    const day = new Date().toISOString().slice(0, 10), deviceCap = positive(env.DAILY_LIMIT, 60), networkCap = positive(env.DAILY_IP_LIMIT, Math.round(deviceCap * 2.5));
    const daily = await readDaily(env, day, net);
    const left = secondsToUtcMidnight(), resetAt = new Date(Date.now() + left * 1000).toISOString();
    const usedBySlot = daily.d[dev] ?? (Object.keys(daily.d).length >= MAX_DEVICES_PER_NETWORK ? daily.d.other || 0 : 0);
    if (usedBySlot >= deviceCap) return json({error: "limit", scope: "device", retry_after: left, reset_at: resetAt}, 429, {"Retry-After": String(left)});
    if (daily.n >= networkCap) return json({error: "limit", scope: "network", retry_after: left, reset_at: resetAt}, 429, {"Retry-After": String(left)});
    let delivered = false;
    const mode = ["ask", "memo"].includes(body.mode) ? body.mode : "chat";
    const memory = String(body.memory || "").replace(/[{}<>]/g, " ").slice(0, 600).trim();
    const target = TARGET[body.target] ? body.target : "nl"; // older app versions send no target → Dutch
    const maxLen = mode === "chat" ? 400 : ["exam11", "exam12"].includes(body.focus) ? 1600 : 600;
    const msgs = (Array.isArray(body.messages) ? body.messages : []).slice(-WINDOW)
      .filter(m => m && (m.role === "user" || m.role === "assistant") && typeof m.content === "string" && m.content.trim())
      .map(m => ({role: m.role, content: m.content.slice(0, maxLen)}));
    const style = ["talk", "teacher", "slow", "exam"].includes(body.style) ? body.style : "teacher";
    if (mode !== "chat") { while (msgs.length && msgs[0].role !== "user") msgs.shift(); if (!msgs.length) return json({error: "empty"}, 400); }
    else if (!msgs.length || msgs[0].role !== "user") msgs.unshift({role: "user", content: msgs.length >= WINDOW ? CONTINUE : openerFor(style)});
    if (mode === "memo") { // one user message with the old notes and the conversation transcript
      const transcript = msgs.map(m => (m.role === "user" ? "Learner: " : "Tutor: ") + m.content).join("\n");
      msgs.splice(0, msgs.length, {role: "user", content: `Old notes:\n${memory || "(none)"}\n\nNew conversation:\n${transcript}`});
    }
    // Preserve recent dialogue but ensure the newest learner turn is authoritative.
    // Previous assistant suggestions are conversation history, not instructions to repeat a drill.
    const notes = learnerNotes(body.profile, mode, memory, style) + (mode === "chat" ? askedNote(msgs) : "") + (mode === "chat" && body.scene === "exam11" ? examScript(body.exam, LANG[body.lang] || "Ukrainian") : "") + (mode === "ask" && body.focus === "exam11" && (body.target || "nl") === "nl" ? EXAM11_COACH(LANG[body.lang] || "Ukrainian") : "");
    const sys = mode === "memo" ? memoSystem(body.lang) : mode === "ask" ? askSystem(target, body.lang, body.level, body.char, notes) : chatSystem(target, body.lang, body.level, body.scene, body.char, notes, style);
    const schema = schemaFor(mode, LANG[body.lang] || "Ukrainian");
    const provider = env.PROVIDER || (env.ANTHROPIC_KEY ? "anthropic" : env.GEMINI_KEY ? "gemini" : "workers-ai");
    await chargeDaily(env, day, net, dev, daily);
    // Don't wait forever for the model: the app shows "try again" instead of hanging.
    const ctl = new AbortController(), timer = setTimeout(() => ctl.abort(), 25000); // shorter than the app's 30 s: the Worker answers "timeout" first, so a retry never overlaps the first call
    try {
      let text = "";
      if (provider === "anthropic") {
        // Structured outputs guarantee valid JSON; low effort keeps replies fast and cheap.
        const r = await fetch("https://api.anthropic.com/v1/messages", {method: "POST", signal: ctl.signal, headers: {"content-type": "application/json", "x-api-key": env.ANTHROPIC_KEY, "anthropic-version": "2023-06-01"},
          body: JSON.stringify({model: env.MODEL || "claude-haiku-5-5", max_tokens: 4000, system: sys, messages: msgs,
            output_config: {effort: env.EFFORT || (mode === "ask" ? "medium" : "low"), format: {type: "json_schema", schema}}})});
        const j = await r.json();
        if (!r.ok) { console.log("anthropic", r.status, JSON.stringify(j).slice(0, 300)); return json({error: "ai"}, 502); }
        if (j.stop_reason === "refusal") return json({error: "refusal"}, 502);
        text = (j.content || []).filter(c => c.type === "text").map(c => c.text).join("");
      } else if (provider === "gemini") {
        const r = await fetch(`https://generativelanguage.googleapis.com/v1beta/models/${env.MODEL || "gemini-3.5-flash-lite"}:generateContent`, {method: "POST", headers: {"Content-Type": "application/json", "x-goog-api-key": env.GEMINI_KEY},
          body: JSON.stringify({systemInstruction: {parts: [{text: sys + "\nReturn ONLY valid JSON matching this schema: " + JSON.stringify(schema)}]}, contents: msgs.map(m => ({role: m.role === "assistant" ? "model" : "user", parts: [{text: m.content}]})), generationConfig: {maxOutputTokens: 1200, temperature: 0.6, responseMimeType: "application/json"}})});
        const j = await r.json(); text = j?.candidates?.[0]?.content?.parts?.map(p => p.text).join("") || "";
      } else {
        const r = await env.AI.run(env.MODEL || "@cf/meta/llama-3.3-70b-instruct-fp8-fast", {messages: [{role: "system", content: sys + "\nReturn ONLY valid JSON matching this schema: " + JSON.stringify(schema)}, ...msgs], max_tokens: 1200, temperature: 0.6});
        text = typeof r?.response === "string" ? r.response : JSON.stringify(r?.response || "");
      }
      const o = parseJSON(text);
      if (mode === "memo") { if (o && typeof o.memory === "string") delivered = true; return json({memory: cut(o && typeof o.memory === "string" ? o.memory : memory, 600)}); }
      if (mode === "ask") {
        if (!o || !o.answer) return json({error: "format"}, 502);
        const ex = (Array.isArray(o.examples) ? o.examples : []).filter(e => e && e.text && ["nl", "en", "fr"].includes(e.lang)).slice(0, 3)
          .map(e => ({lang: e.lang, text: cut(e.text, 200), translation: cut(e.translation, 200)}));
        delivered = true;
        return json({answer: cut(o.answer, 1500), examples: ex});
      }
      const reply = o && (o.reply || o.reply_nl);
      if (!reply) return json({error: "format"}, 502);
      const k = o.correction;
      const lastUser = String((msgs.filter(m => m.role === "user").pop() || {}).content || "").replace(/\[spoken;[^\]]*\]\s*$/, "").trim();
      const heard = String((msgs.filter(m => m.role === "user").pop() || {}).content || "").match(/\[spoken; other possible transcriptions: ([^\]]*)\]\s*$/);
      const alternatives = heard ? heard[1].split(" | ").map(sentenceKey) : [];
      const major = !!k && k.severity === "major";
      // has_error + severity are part of the answer: the app only shows a correction card (and the exam only counts a retry) when has_error is true.
      let c = k && k.corrected && k.has_error !== false ? {has_error: true, severity: major ? "major" : "minor", original: cut(k.original || lastUser, 300), corrected: cut(latin(k.corrected), 300), explanation: cut(k.explanation, 300)} : null;
      if (c && sentenceKey(c.corrected) === sentenceKey(lastUser)) c = null;                     // "corrected" is what they wrote: there was nothing to fix
      else if (c && style === "talk" && !major) c = null;                                       // free talk: only mistakes that block understanding
      else if (c && !major && alternatives.includes(sentenceKey(c.corrected))) c = null;      // voice: the recognizer also heard the correct sentence, so it is an artefact, not the learner's mistake
      const said = o.learner_in_target ? cut(latin(o.learner_in_target), 300) : "";
      if (said && /[\u0400-\u04FF\u0600-\u06FF]/.test(lastUser) && (!c || /[\u0400-\u04FF\u0600-\u06FF]/.test(c.corrected)))
        c = {has_error: true, severity: "major", original: cut(lastUser, 300), corrected: said, explanation: (SAY_IT[body.lang] || SAY_IT.en)(body.target)}; // wrong language = major
      delivered = true;
      return json({reply: cut(latin(reply), 400), reply_nl: cut(latin(reply), 400), translation: cut(o.translation, 400), correction: c});
    } catch (e) {
      const late = e && e.name === "AbortError";
      return json({error: late ? "timeout" : "ai"}, late ? 504 : 502);
    } finally {
      clearTimeout(timer);
      if (!delivered) { const p = chargeDaily(env, day, net, dev, daily, -1); if (ctx && ctx.waitUntil) ctx.waitUntil(p); else await p; }
    }
  }
};

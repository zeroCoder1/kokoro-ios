import Testing
@testable import KokoroSwift

/// A cross-section of everyday Hindi: pronouns, numerals in word form, common
/// verbs and nouns, nukta loanwords and the dotted retroflex flaps. Anything
/// the phonemizer emits for these has to be a Kokoro token, so a new mapping
/// mistake fails the build instead of being dropped silently at tokenization.
private let commonHindiWords: [String] = [
    "नमस्ते", "धन्यवाद", "कृपया", "हाँ", "नहीं", "आज", "कल", "अभी",
    "यहाँ", "वहाँ", "कहाँ", "क्यों", "कैसे", "कब", "कौन", "क्या",
    "कुछ", "सब", "बहुत", "थोड़ा", "अच्छा", "बुरा", "बड़ा", "छोटा",
    "नया", "पुराना", "लंबा", "छोटी", "तेज़", "धीमा", "पानी", "खाना",
    "रोटी", "चावल", "दूध", "चाय", "फल", "सब्ज़ी", "नमक", "चीनी",
    "घर", "कमरा", "दरवाज़ा", "खिड़की", "सड़क", "बाज़ार", "दुकान", "स्कूल",
    "अस्पताल", "मंदिर", "आदमी", "औरत", "लड़का", "लड़की", "बच्चा", "माता",
    "पिता", "भाई", "बहन", "दोस्त", "काम", "नौकरी", "पैसा", "समय",
    "दिन", "रात", "सुबह", "शाम", "हफ़्ता", "महीना", "साल", "देश",
    "भारत", "दिल्ली", "शहर", "गाँव", "राज्य", "सरकार", "नेता", "चुनाव",
    "पढ़ना", "लिखना", "बोलना", "सुनना", "देखना", "जाना", "आना", "करना",
    "होना", "देना", "लेना", "पीना", "सोना", "उठना", "बैठना", "चलना",
    "दौड़ना", "रुकना", "बढ़ना", "गढ़ना", "किताब", "कलम", "कागज़", "मेज़",
    "कुर्सी", "गाड़ी", "ट्रेन", "हवाई", "रास्ता", "पुल", "सवाल", "जवाब",
    "बात", "कहानी", "गाना", "खेल", "फ़िल्म", "ख़बर", "अख़बार", "तस्वीर",
]

/// Regression guard for the ड़ / ढ़ mapping, which must never reintroduce the
/// `.` that espeak's `r.` mnemonic leaks — a sentence break mid-word. The flap
/// itself was settled by ear: `ɽ` is the accurate IPA but is untrained here,
/// a literal `r` renders stop-like without the `.` that always followed it in
/// training, and `ɾ` is the rhotic every र already uses.
@Test(arguments: ["बड़ा", "पढ़ना", "थोड़ा", "लड़की", "सड़क", "बढ़ना", "लड़का", "बढ़िया"])
func hindiRetroflexFlapsEmitNoSentenceBreak(word: String) {
  let phonemes = HindiPhonemizer.phonemize(word)

  #expect(!phonemes.contains("."), "\(word) -> \(phonemes)")
  #expect(phonemes.contains("ɖ"), "\(word) -> \(phonemes)")
}

@Test func hindiRetroflexFlapsUseKokoroTokens() {
  #expect(HindiPhonemizer.phonemize("बड़ा") == "bˈʌɖaː")
  #expect(HindiPhonemizer.phonemize("थोड़ा") == "tʰˈoːɖaː")
  #expect(HindiPhonemizer.phonemize("पढ़ना") == "pˈʌɖʰnaː")
  // The nukta may be written precomposed or decomposed; both are one flap.
  #expect(HindiPhonemizer.phonemize("पढ़ना") == HindiPhonemizer.phonemize("पढ़ना"))
}

/// Schwa fronting before `h` is real in कहना, रहना and पहला, where the `h` is
/// followed by another consonant. Word-finally it is not: fronting there gave
/// आग्रह as /aːɡɾɛh/, which is heard as आगरे.
@Test func hindiSchwaFrontingSkipsWordFinalH() {
  #expect(HindiPhonemizer.phonemize("आग्रह") == "ˈaːɡɾəh")
  #expect(HindiPhonemizer.phonemize("प्रवाह") == "pɾəʋˈaːh")
  #expect(HindiPhonemizer.phonemize("उत्साह") == "ʊtsˈaːh")
  #expect(HindiPhonemizer.phonemize("निर्वाह") == "nɪrʋˈaːh")

  // The words the rule was written for are untouched.
  #expect(HindiPhonemizer.phonemize("कहना") == "kˈɛhnaː")
  #expect(HindiPhonemizer.phonemize("रहना") == "ɾˈɛhnaː")
  #expect(HindiPhonemizer.phonemize("पहला") == "pˈɛhlaː")
  #expect(HindiPhonemizer.phonemize("बहुत") == "bˈʌhʊt")
}

/// Deleting the schwa in वाराणसी strands the ɳ in the coda, where it is heard
/// as nasalization on the vowel before it — वारांसी. The name has four
/// syllables, so the schwa is spelled out.
@Test func hindiKeepsTheSchwaInVaranasi() {
  // The override is written out, so it has to honour the final-vowel rule
  // itself: espeak ends this on a short i and so do we.
  #expect(HindiPhonemizer.phonemize("वाराणसी") == "ʋaːɾˈaːɳəsi")
}

// MARK: - Rules verified against espeak-ng
//
// Every expectation below was read off `espeak-ng -v hi -q --ipa`, which is
// the distribution Kokoro's Hindi voices were trained on. Re-check with
// Tools/espeak-diff.py before changing any of them.

/// espeak opens a word written with अ on ʌ, stressed or not. Reading it as ə
/// is why अंतरराष्ट्रीय was heard starting on इ.
@Test func hindiWordInitialAIsOpenNotSchwa() {
  #expect(HindiPhonemizer.phonemize("अदालत") == "ʌdˈaːlət")
  #expect(HindiPhonemizer.phonemize("अस्पताल") == "ʌspətˈaːl")
  #expect(HindiPhonemizer.phonemize("अख़बार") == "ʌxbˈaːɾ")
  #expect(HindiPhonemizer.phonemize("अनुमान") == "ʌnʊmˈaːn")
}

/// espeak never ends a Hindi word on a long high vowel.
@Test func hindiFinalHighVowelsAreShort() {
  #expect(HindiPhonemizer.phonemize("पानी") == "pˈaːni")
  #expect(HindiPhonemizer.phonemize("रोटी") == "ɾˈoːʈi")
  #expect(HindiPhonemizer.phonemize("भेजी") == "bʰˈeːɟi")
  #expect(HindiPhonemizer.phonemize("मंत्री") == "mˈʌntɾi")
}

/// ...but only when the vowel actually ends the word. A following consonant
/// keeps it long.
@Test func hindiHighVowelsStayLongBeforeAConsonant() {
  #expect(HindiPhonemizer.phonemize("ज़मीन") == "zəmˈiːn")
  #expect(HindiPhonemizer.phonemize("क़ानून") == "qaːnˈuːn")
}

/// A written virama gives the trill; an inherent schwa that deletion removed
/// keeps the flap.
@Test func hindiRhoticSplitsOnTheWrittenVirama() {
  #expect(HindiPhonemizer.phonemize("निर्माण") == "nɪrmˈaːɳ")
  #expect(HindiPhonemizer.phonemize("निर्वाह") == "nɪrʋˈaːh")
  #expect(HindiPhonemizer.phonemize("कुर्सी") == "kˈʊrsi")

  // सरकार has no virama — the schwa was deleted, so the flap stays.
  #expect(HindiPhonemizer.phonemize("सरकार") == "səɾkˈaːɾ")
  #expect(HindiPhonemizer.phonemize("रवाना") == "ɾəʋˈaːnaː")
}

/// A hyphen written tight between two words joins them with nothing between:
/// espeak reads साथ-साथ as one run, not two words with a pause. A space there
/// is token 16, which the model never saw at that spot.
@Test func hindiTightHyphensJoinWithoutASpace() {
  #expect(HindiPhonemizer.phonemize("साथ-साथ") == "sˈaːtʰsˈaːtʰ")
  #expect(HindiPhonemizer.phonemize("भारत-चीन") == "bʰˈaːɾətcˈiːn")
  #expect(HindiPhonemizer.phonemize("आना-जाना") == "ˈaːnaːɟˈaːnaː")
}

/// A hyphen with space around it, or an en dash, is an ordinary word break.
@Test func hindiSpacedHyphensAndEnDashesStayWordBreaks() {
  #expect(HindiPhonemizer.phonemize("अपने- अपने") == "ˈʌpneː ˈʌpneː")
  #expect(HindiPhonemizer.phonemize("अलग - अलग") == "ˈʌləɡ ˈʌləɡ")
  #expect(HindiPhonemizer.phonemize("भारत–चीन") == "bʰˈaːɾət cˈiːn")
  #expect(HindiPhonemizer.phonemize("यह -") == "jˈʌh")
}

/// Punctuation with no Kokoro token is dropped rather than passed through. The
/// tokenizer would discard it anyway, but emitting it makes a training label
/// unusable and hides the real word boundary.
@Test func hindiEmitsOnlyPunctuationKokoroHasTokensFor() throws {
  let vocab = try KokoroConfig.loadConfig().vocab
  let awkward = "यह — ठीक है… \"हाँ\" (शायद); नहीं: बस, अलग-अलग ~ ठीक * है #1"

  let phonemes = HindiPhonemizer.phonemize(awkward)
  let unsupported = phonemes.unicodeScalars.filter { vocab[String($0)] == nil }

  #expect(unsupported.isEmpty, "\(phonemes)")
  // The punctuation Kokoro does have still survives.
  #expect(phonemes.contains("…"))
  #expect(phonemes.contains(","))
}

/// A Devanagari-spelled acronym is a sequence of letter names, not one word.
@Test func hindiDevanagariAcronymsAreReadLetterByLetter() {
  #expect(HindiPhonemizer.phonemize("एनडीआरएफ") == "ˈeːn ɖˈi ˈaːɾ ˈeːf")
  #expect(HindiPhonemizer.phonemize("बीजेपी") == "bˈi ɟˈeː pˈi")
  #expect(HindiPhonemizer.phonemize("सीबीआई") == "sˈi bˈi ˈaːi")
  #expect(HindiPhonemizer.phonemize("पीएम") == "pˈi ˈeːm")
}

/// The nukta-less एफ that most copy uses was read as /pʰ/, so एनडीआरएफ ended
/// in "eph" rather than "eff".
@Test(arguments: ["एनडीआरएफ", "एसडीआरएफ", "बीएसएफ", "सीआरपीएफ", "आईएएफ"])
func hindiAcronymsEndingInEfUseTheLabiodental(acronym: String) {
  let phonemes = HindiPhonemizer.phonemize(acronym)

  #expect(phonemes.hasSuffix("ˈeːf"), "\(acronym) -> \(phonemes)")
  #expect(!phonemes.contains("pʰ"), "\(acronym) -> \(phonemes)")
}

@Test(arguments: commonHindiWords)
func hindiPhonemesAreAllKokoroVocabulary(word: String) throws {
  let vocab = try KokoroConfig.loadConfig().vocab
  let phonemes = HindiPhonemizer.phonemize(word)
  let unsupported = phonemes.unicodeScalars.filter { vocab[String($0)] == nil }

  #expect(!phonemes.isEmpty, "\(word) phonemized to nothing")
  #expect(
    unsupported.isEmpty,
    "\(word) -> \(phonemes) emits \(unsupported.map { "U+" + String($0.value, radix: 16) })"
  )
}

@Test(arguments: commonHindiWords)
func hindiPhonemesSurviveTokenization(word: String) throws {
  _ = try KokoroConfig.loadConfig()
  let phonemes = HindiPhonemizer.phonemize(word)

  #expect(
    Tokenizer.tokenize(phonemizedText: phonemes).count == phonemes.unicodeScalars.count
  )
}

/// Space is token 16. A space in front of punctuation, or a doubled space, is
/// a pause the model was never trained to produce there.
@Test(arguments: [
  "यह शब्द है.",
  "क्या यह ठीक है?",
  "रुको!",
  "पहला,  दूसरा और तीसरा.",
  "नमस्ते। धन्यवाद॥",
  "वह बड़ा शहर है, बहुत बड़ा.",
])
func hindiPhonemizerNeverSpacesBeforePunctuation(sentence: String) {
  let phonemes = HindiPhonemizer.phonemize(sentence)

  #expect(!phonemes.contains("  "), "double space in \(phonemes)")
  #expect(!phonemes.contains(" ."), "space before period in \(phonemes)")
  #expect(!phonemes.contains(" ,"), "space before comma in \(phonemes)")
  #expect(!phonemes.contains(" ?"), "space before question mark in \(phonemes)")
  #expect(!phonemes.contains(" !"), "space before exclamation in \(phonemes)")
}

#if canImport(MisakiSwift)
/// The Misaki fallback needs an MLX Metal runtime, so these all stay on the
/// native Hindi path: Devanagari, expanded numbers, acronyms and the
/// transliteration lexicon.
@Test(arguments: [
  "यह 2024 में ₹1,50,000 था.",
  "15% वृद्धि, 25° तापमान.",
  "BJP ने IPL जीता.",
  "मुझे  ATM  से  पैसे  चाहिए.",
  "१५ अगस्त को छुट्टी है!",
])
func hindiG2PNeverSpacesBeforePunctuation(sentence: String) throws {
  let processor = HindiG2PProcessor()
  try processor.setLanguage(.hi)

  let phonemes = try processor.process(input: sentence).0

  #expect(!phonemes.contains("  "), "double space in \(phonemes)")
  #expect(!phonemes.contains(" ."), "space before period in \(phonemes)")
  #expect(!phonemes.contains(" ,"), "space before comma in \(phonemes)")
  #expect(!phonemes.contains(" !"), "space before exclamation in \(phonemes)")
  #expect(!phonemes.hasPrefix(" "), "leading space in \(phonemes)")
  #expect(!phonemes.hasSuffix(" "), "trailing space in \(phonemes)")
}

@Test func hindiG2PReadsAcronymsAsDevanagariLetterNames() throws {
  let processor = HindiG2PProcessor()
  try processor.setLanguage(.hi)

  #expect(
    try processor.process(input: "BJP").0 == HindiPhonemizer.phonemize("बीजेपी")
  )
  #expect(
    try processor.process(input: "IPL").0 == HindiPhonemizer.phonemize("आईपीएल")
  )
  // Seven letters is a word, not an acronym, so it stays with Misaki.
  #expect(try processor.process(input: "यह UPI है.").0
    == HindiPhonemizer.phonemize("यह यूपीआई है."))
}

@Test func hindiG2PSpeaksCommonEnglishTermsInHindi() throws {
  let processor = HindiG2PProcessor()
  try processor.setLanguage(.hi)

  #expect(
    try processor.process(input: "WhatsApp").0 == HindiPhonemizer.phonemize("व्हाट्सऐप")
  )
  #expect(
    try processor.process(input: "मुझे Google पर").0
      == HindiPhonemizer.phonemize("मुझे गूगल पर")
  )
}

/// The transliteration lexicon and the acronym letter names are new
/// Devanagari sources feeding the phonemizer, so they get the same
/// vocabulary guarantee as ordinary Hindi words.
@Test(arguments: [
  "WhatsApp", "Google", "Facebook", "YouTube", "Twitter", "Instagram",
  "online", "mobile", "internet", "computer", "email", "video", "photo",
  "app", "website", "server", "bank", "ATM", "office", "doctor", "hospital",
  "police", "train", "bus", "ticket", "market", "court", "minister",
  "report", "update",
  "BJP", "IPL", "UPI", "GST", "RBI", "CBI", "NDA", "PM", "MLA", "SUV",
  "ABCDEF", "XYZ", "QW",
])
func hindiG2PLatinRenderingsAreAllKokoroVocabulary(word: String) throws {
  let processor = HindiG2PProcessor()
  try processor.setLanguage(.hi)
  let vocab = try KokoroConfig.loadConfig().vocab

  let phonemes = try processor.process(input: word).0
  let unsupported = phonemes.unicodeScalars.filter { vocab[String($0)] == nil }

  #expect(!phonemes.isEmpty, "\(word) phonemized to nothing")
  #expect(
    unsupported.isEmpty,
    "\(word) -> \(phonemes) emits \(unsupported.map { "U+" + String($0.value, radix: 16) })"
  )
}

@Test func hindiG2PDropsSymbolsWithNoKokoroToken() throws {
  let processor = HindiG2PProcessor()
  try processor.setLanguage(.hi)
  let vocab = try KokoroConfig.loadConfig().vocab

  let phonemes = try processor.process(input: "तापमान 25° © है.").0
  let unsupported = phonemes.unicodeScalars.filter { vocab[String($0)] == nil }

  #expect(unsupported.isEmpty, "\(phonemes)")
}

@Test func hindiG2PExpandsNumbersOntoTheHindiPath() throws {
  let processor = HindiG2PProcessor()
  try processor.setLanguage(.hi)

  #expect(
    try processor.process(input: "यह 2024 में था.").0
      == HindiPhonemizer.phonemize("यह दो हज़ार चौबीस में था.")
  )
}
#endif

#if canImport(MisakiSwift)
/// The danda ends a Hindi sentence and Kokoro has no token for it. It is
/// neutral to the run splitter, so it flushed straight to the output without
/// passing through HindiPhonemizer's own conversion, and the tokenizer then
/// dropped it — taking the sentence break with it. This is what made a
/// headline run into the line after it.
@Test(arguments: [
  "राहत की उड़ान नेपाल रवाना। उन्होंने कहा।",
  "यह ठीक है॥",
  "BJP और IPL की खबर।",
  "एनडीआरएफ की टीम पहुँची।",
])
func hindiG2PTurnsTheDandaIntoASentenceBreak(sentence: String) throws {
  let vocab = try KokoroConfig.loadConfig().vocab
  let processor = HindiG2PProcessor()
  try processor.setLanguage(.hi)

  let phonemes = try processor.process(input: sentence).0

  #expect(phonemes.contains("."), "no sentence break in \(phonemes)")
  #expect(!phonemes.contains("।"), "danda survived into \(phonemes)")
  #expect(!phonemes.contains("॥"), "double danda survived into \(phonemes)")
  let unsupported = phonemes.unicodeScalars.filter { vocab[String($0)] == nil }
  #expect(unsupported.isEmpty, "\(phonemes)")
}

/// Nothing the run splitter flushes may be a character Kokoro cannot tokenize.
@Test func hindiG2POnlyEmitsPunctuationKokoroHasTokensFor() throws {
  let vocab = try KokoroConfig.loadConfig().vocab
  let processor = HindiG2PProcessor()
  try processor.setLanguage(.hi)

  let phonemes = try processor.process(
    input: "यह — ठीक है… «शायद» ‹हाँ› अलग-अलग। बस॥"
  ).0
  let unsupported = phonemes.unicodeScalars.filter { vocab[String($0)] == nil }

  #expect(unsupported.isEmpty, "\(phonemes)")
}
#endif

/// ड़ and र are different letters and must not collapse into one sound:
/// बड़ा is "bada", बरा is "bara".
@Test func hindiKeepsTheDottedRetroflexApartFromR() {
  #expect(HindiPhonemizer.phonemize("बड़ा") != HindiPhonemizer.phonemize("बरा"))
  #expect(HindiPhonemizer.phonemize("बड़ा") == "bˈʌɖaː")
  #expect(HindiPhonemizer.phonemize("बरा") == "bˈʌɾaː")

  // And र itself is untouched — सरकार still ends in the flap.
  #expect(HindiPhonemizer.phonemize("सरकार") == "səɾkˈaːɾ")
  #expect(HindiPhonemizer.phonemize("करोड़") == "kəɾˈoːɖ")
}

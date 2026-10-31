# Medicine sheet: ind-mr-fw2 (adinathauti)

Pack: ind-mr-fw2 · Language: Marathi (Devanagari) · 500 documents

Diseases found more than 5 times: D3 (281), C3 (112), A5 (39), C2 (38), A1 (30), A3 (27), C1 (17).

---

## Medicine 1 — D3: Mixed language (281 docs)

1. **Disease:** D3 — Romanised or Latin-script words embedded in Marathi Devanagari text.
   Count: 281 / 500.
   Examples:
   - `00eed90bde196e9c` — headline starts with "How To Find Sweet Watermelon:"
   - `45099f1718f10018` — headline starts with "Lioness And leopard Fight Viral Video :"
   - `924d41c82dfe4138` — headline starts with "Viral Video:"

2. **Medicine:** This is natural code-switching in Marathi journalism — English proper nouns,
   brand names, and viral-content headlines routinely appear in Latin script alongside Devanagari.
   No removal or substitution is warranted; the mixing is not an error.
   Flag only (label D3); do not alter the text.

   ```python
   def has_d3(text: str) -> bool:
       import re
       deva  = sum(1 for c in text if 'ऀ' <= c <= 'ॿ')
       latin = len(re.findall(r'[a-zA-Z]{3,}', text))
       return deva > 50 and latin > 0
   ```

3. **Action:** fix — keep the document; no text change. The label records the mixing for
   downstream analysis but the document is not cleaned.

4. **Harm test:** Gold set for Marathi (mar_Deva) not available locally (owned by Data A/B
   teams). Medicine makes no text changes, so 0 gold documents would be altered or dropped.

5. **Side effects:** None — the medicine is a no-op (label only).

---

## Medicine 2 — C3: Truncated document (112 docs)

1. **Disease:** C3 — Document ends mid-sentence with no terminal punctuation.
   Count: 112 / 500.
   Examples:
   - `a04bc6869aca8184` — ends `…कामाविषयी चर्चा झाली, अन्य नाही."` (quoted speech cut)
   - `626fc9159542b61c` — ends `Tags: Diabetes, Health, Health Tips, Lifestyle` (boilerplate tag list)
   - `5c05e18231a55839` — ends `महाराष्ट्र ठळक बातम्या | Maharashtra Times` (site footer)

2. **Medicine:** Drop any document whose text (after right-stripping whitespace) does not end
   with a recognised terminal character from the set:
   `.  !  ?  ।  ॥  "  "  '  …  —  –  ]  }  )  ⭕`

   ```python
   import re
   _TERMINAL = re.compile(r'[.!?\n"\'।॥…\]}\)""—–⭕]\s*$')

   def should_drop_c3(text: str) -> bool:
       return len(text) >= 200 and not _TERMINAL.search(text.rstrip())
   ```

3. **Action:** drop — a truncated document teaches the model that text can end anywhere.

4. **Harm test:** Gold set not available locally. The regex is conservative (large terminal
   character set) so false-positive rate on clean Marathi prose should be very low.

5. **Side effects:** Documents that end with a closing double-quote `"` (U+201D) may be
   incorrectly passed if the quoted sentence itself is truncated inside the quote. Also,
   boilerplate footers ending with a site name (no punctuation) will be correctly caught.

---

## Medicine 3 — A5: Wrong normal form (39 docs)

1. **Disease:** A5 — Devanagari characters stored in NFD or a mixed normal form instead of NFC.
   Count: 39 / 500.
   Examples:
   - `489da5c3b5d9ffe2` — nukta or matra written as a separate combining character
   - `8445992d98332735` — composed and decomposed forms of the same akshara appear in one doc
   - `3621f9c755f06081` — vowel sign stored as combining sequence instead of precomposed codepoint

2. **Medicine:** Apply NFC normalisation to the full text.

   ```python
   import unicodedata

   def fix_a5(text: str) -> str:
       return unicodedata.normalize('NFC', text)
   ```

3. **Action:** fix — normalise in place; the rendered text is identical but the byte sequence
   becomes canonical.

4. **Harm test:** Gold set not available locally. NFC is idempotent on already-NFC text, so
   the medicine changes 0 bytes in clean documents.

5. **Side effects:** NFKC would additionally fold compatibility characters (e.g. Indic digits
   → ASCII digits), which is undesirable. NFC does not do this. Safe for Devanagari.

---

## Medicine 4 — C2: Repeated lines (38 docs)

1. **Disease:** C2 — The same non-empty line appears two or more times in one document.
   Count: 38 / 500.
   Examples:
   - `654e623661c0b8c6` — "सर्वात आधी वाचा विश्वासार्ह मराठी न्यूज वेबसाइट News18 लोकमतवर." repeated
   - `08dbb49c409f6de0` — section separator line repeated
   - `05b7b743f394e916` — footer line repeated

2. **Medicine:** Remove all duplicate occurrences of a line, keeping only the first.

   ```python
   def fix_c2(text: str) -> str:
       seen = set()
       out  = []
       for line in text.split('\n'):
           key = line.strip()
           if key and key in seen:
               continue
           seen.add(key)
           out.append(line)
       return '\n'.join(out)
   ```

3. **Action:** fix — remove the duplicate lines; keep the document.

4. **Harm test:** Gold set not available locally. The medicine only removes lines that are
   exact string duplicates of a prior line; unique lines are never touched.

5. **Side effects:** Intentional repetition (e.g. a poem or a list with a repeated refrain)
   would be incorrectly de-duplicated. Rare in news prose.

---

## Medicine 5 — A1: Invisible junk characters (30 docs)

1. **Disease:** A1 — Zero-width space (U+200B), BOM (U+FEFF), soft hyphen (U+00AD), or
   Unicode bidi control characters present in the text.
   Count: 30 / 500.
   Examples:
   - `a04bc6869aca8184` — soft hyphen or ZWSP embedded in Devanagari word
   - `29f9f308afd0859e` — ZWSP between words
   - `00eed90bde196e9c` — BOM or bidi mark in headline

2. **Medicine:** Strip the offending invisible characters. ZWJ (U+200D) and ZWNJ (U+200C) are
   NOT removed — they are required for correct Devanagari/Hindi conjunct rendering.

   ```python
   import re
   _A1_RE = re.compile(
       r'[​﻿­'      # ZWSP, BOM, soft hyphen
       r'‪-‮'            # bidi embed/override
       r'⁦-⁩]'           # bidi isolate
   )

   def fix_a1(text: str) -> str:
       return _A1_RE.sub('', text)
   ```

3. **Action:** fix — strip the characters in place.

4. **Harm test:** Gold set not available locally. The regex is a precise allowlist of
   invisible junk; it does not touch ZWJ/ZWNJ or any visible character.

5. **Side effects:** A U+00AD soft hyphen used deliberately for line-breaking in long compound
   words would be removed, but this is acceptable — soft hyphens are a typographic hint, not
   semantic content.

---

## Medicine 6 — A3: Mojibake (27 docs)

1. **Disease:** A3 — UTF-8 Devanagari text that was decoded as Latin-1 or Windows-1252,
   producing sequences like `Ã¤`, `à¤¹`, `â€™`.
   Count: 27 / 500.
   Examples:
   - `97333df118ec5df2` — Devanagari script names for other languages appear as Latin garbage
   - `e1dc211abdf5bf39` — article body contains mojibake sequences mid-paragraph
   - `6169b09fe7801904` — mixed content with both clean Devanagari and mojibake spans

2. **Medicine:** Re-encode: decode the text as Latin-1, then re-encode as UTF-8 and decode again.
   Only apply if the document contains mojibake markers; otherwise leave unchanged.

   ```python
   import re
   _MOJI_RE = re.compile(r'[ÃÂ][\x80-\xBF]|â€[\x98-\x9E™]')

   def fix_a3(text: str) -> str:
       if not _MOJI_RE.search(text):
           return text
       try:
           return text.encode('latin-1').decode('utf-8')
       except (UnicodeEncodeError, UnicodeDecodeError):
           return text  # partial mojibake — leave for human review
   ```

3. **Action:** fix — attempt re-encoding; if it fails (partial mojibake), keep original and
   flag for manual review.

4. **Harm test:** Gold set not available locally. The medicine is gated on the presence of
   mojibake markers, so clean documents are never re-encoded.

5. **Side effects:** A document with a genuine Latin-1 loanword that happens to match the
   mojibake pattern could be wrongly re-encoded. The guard regex is conservative; risk is low.

---

## Medicine 7 — C1: Boilerplate (17 docs)

1. **Disease:** C1 — Scraper-inserted footer lines: site navigation, "Tags:", newsletter
   prompts, and source attribution lines from Marathi news aggregators.
   Count: 17 / 500.
   Examples:
   - `626fc9159542b61c` — ends with `Tags: Diabetes, Health, Health Tips, Lifestyle`
   - `5c05e18231a55839` — ends with `Maharashtra News, Latest Maharashtra News in Marathi…`
   - `c8ad1802a6fbb058` — ends with `महाराष्ट्र ठळक बातम्या | Maharashtra Times`

2. **Medicine:** Strip trailing boilerplate lines that match known footer patterns.

   ```python
   import re
   _C1_FOOTER = re.compile(
       r'\n(?:Tags\s*:.*|'
       r'Maharashtra(?:Times)?\s*News.*|'
       r'.*News18.*लोकमतवर\.?|'
       r'.*विश्वासार्ह मराठी न्यूज.*|'
       r'.*ठळक बातम्या.*)\s*$',
       re.IGNORECASE
   )

   def fix_c1(text: str) -> str:
       return _C1_FOOTER.sub('', text).rstrip()
   ```

3. **Action:** fix — strip the footer lines; keep the document.

4. **Harm test:** Gold set not available locally. The patterns are anchored to the end of the
   document (`$`) and match specific known strings, so mid-document false positives are unlikely.

5. **Side effects:** A news article that genuinely quotes a "Maharashtra Times" headline inside
   the body (not as a footer) would not be matched because the pattern is end-anchored. Safe.

# Medicine sheet: code-js-ts (AjaySnl)

Write one section for each disease that you found more than five times.

---

## Medicine 1 — B3: StarCoder ghost tokens

### 1. Disease

**Code:** B3  
**Count in pack:** 258 documents out of 500  
**Description:** Documents from `bigcode/starcoderdata` carry StarCoder preprocessing tokens embedded in their text. These tokens were inserted by StarCoder's data pipeline to mark metadata (repository name, filename, star count) and to anonymise personal data (email addresses and author names). They are not part of the original source code. Training V5 on text containing these tokens would teach the model to generate them as plain text.

The tokens observed:

| Token | Docs containing token | Total occurrences |
|---|---|---|
| `<gh_stars>` | 107 | 107 |
| `<filename>` | 105 | 105 |
| `<reponame>` | 101 | 101 |
| `<NAME>` | 14 | 25 |
| `<EMAIL>` | 10 | 29 |

`<filename>`, `<reponame>`, and `<gh_stars>` each appear at most once per document (always as a prefix block). `<EMAIL>` and `<NAME>` may appear multiple times per document (once for each anonymised value).

**Four examples:**

**Example A — `<filename>` and `<gh_stars>` prefix block:**
- `doc_id=c38890881e99e48e`
- Text starts: `<filename>src/extended-repeater.js<gh_stars>0\nimport { NotImplementedError }...`
- `'<filename>'` at offset 0; `'<gh_stars>'` at offset 34

**Example B — `<reponame>` prefix:**
- `doc_id=c09dabc135210035`
- Text starts: `<reponame>heminjohnson/Node-Chat-App-With-Socket.io\nvar expect = require('expect')`
- `'<reponame>'` at offset 0

**Example C — `<EMAIL>` anonymisation token in test code:**
- `doc_id=ec27a58ce8941db1`
- Text contains: `...rule.passes('<EMAIL>', { primary_email: '<EMAIL>' })...`
- `'<EMAIL>'` at offsets 202, 230, 328 (multiple occurrences; 29 total across 10 documents)

**Example D — `<NAME>` author anonymisation token in licence header:**
- `doc_id=ac23df9698407bac`
- Text starts: `/** * Copyright (c) 2020 <NAME> * Licensed under the Apache License...`
- `'<NAME>'` at offset 32

---

### 2. Medicine

**Rule in words:**

1. Strip the StarCoder prefix block from the **absolute beginning** of the document. The block consists of one to five consecutive lines, each starting with `<reponame>`, `<filename>`, or `<gh_stars>` (in any order), followed by their value on the same line. The match must begin at character position 0.
2. Replace any remaining `<EMAIL>` tokens in the document body with `user@example.com`.
3. Replace any remaining `<NAME>` tokens with `[AUTHOR]`.
4. Remove any other ghost-marker tokens (chat template tokens) if present.

**Rule in code:**

```python
import re

# \A anchors to the absolute start of the string.
# This prevents the regex from matching a <filename>-like line in the middle
# of a document body. Using ^ with re.MULTILINE would incorrectly match
# any line starting with the token, not only the document's first line.
_STARCODER_LINE = r'<(?:reponame|filename|gh_stars)>[^\n]*\n?'
STARCODER_PREFIX_RE = re.compile(r'\A(?:' + _STARCODER_LINE + r'){1,5}')

# Replace <EMAIL> anonymisation tokens.
# user@example.com uses the IANA-reserved example.com domain (RFC 2606)
# and is a syntactically valid RFC 5321 email address.
# The old placeholder [email protected] was NOT RFC 5321 valid.
EMAIL_TOKEN_RE = re.compile(r'<EMAIL>')

# Replace <NAME> anonymisation tokens.
NAME_TOKEN_RE = re.compile(r'<NAME>')

# Remove other ghost markers (chat-template tokens) if present.
OTHER_GHOST_RE = re.compile(
    r'<\|im_start\|>|<\|im_end\|>|<\|endoftext\|>'
    r'|\[INST\]|\[/INST\]|<<SYS>>|<</SYS>>'
    r'|<think>|</think>'
)

def fix_b3(text: str) -> str:
    """Strip StarCoder prefix and replace anonymisation tokens."""
    text = STARCODER_PREFIX_RE.sub('', text, count=1)
    text = EMAIL_TOKEN_RE.sub('user@example.com', text)
    text = NAME_TOKEN_RE.sub('[AUTHOR]', text)
    text = OTHER_GHOST_RE.sub('', text)
    return text
```

---

### 3. Action

**Fix the text.** The underlying code is valid; only the StarCoder metadata prefix and anonymisation tokens need to be removed or replaced. Dropping the whole document would be wasteful for 258 otherwise-clean files.

Exception: if B3 co-occurs with E1 (compiled/generated code) or E3 (embedded secrets), the verdict is `drop` regardless of this medicine, because the other disease takes precedence.

---

### 4. Harm test

#### 4a. Regression tests (automated, pass/fail)

20 unit tests covering:

| Test group | Cases covered | Result |
|---|---|---|
| Anchor correctness | Valid prefix stripped; body token NOT stripped; no-prefix doc unchanged; trailing blank after prefix | 6/6 pass |
| Token-like strings in code | `<filename>` in `//` comment; in string literal; in object value; in JSX attr (with whitespace); at non-zero line start | 5/5 pass |
| EMAIL replacement | String-literal context; known test-literal regression; EMAIL inside prefix block | 3/3 pass |
| NAME replacement | Copyright header; doc without token | 2/2 pass |
| OTHER_GHOST_RE | Chat token stripped from body; `<s>` HTML tag preserved; chat token in string literal removed; chat token in comment removed | 4/4 pass |

**Total: 20/20 pass.**

Key result for the anchor fix: test `1c` confirms that a `<filename>` line in the document body is **not** stripped with the `\A` anchor. The old `re.MULTILINE` version incorrectly stripped it (test `1d` documents the bug).

Tests `5c` and `5d` document that `OTHER_GHOST_RE` removes ghost tokens globally — including from inside string literals and comments. This is the intended behaviour (see side effect 8 below) and is tested, not assumed.

#### 4b. Proxy harm test (informative, not definitive)

**Official gold set status: BLOCKED — gold set unavailable.**

The official JavaScript/TypeScript gold set (≥ 200 documents reviewed by two readers and marked `clean`) has not yet been released by the Data A team. The following proxy result is non-definitive and is provided for orientation only.

| Metric | Value |
|---|---|
| Proxy set | 233 documents labelled `clean` in the full-500 diagnosis |
| Docs changed by `fix_b3()` | 0 |
| Docs dropped by `fix_b3()` | 0 |
| Percentage affected | 0.00% |
| Passes 1% threshold? | Yes (informatively) |

**What this proxy test does and does not cover:**

The 233 proxy documents were labelled `clean` by automated scanning (every character checked by the detection functions). Per DISEASES.md, `read=partial` applies only when the reviewer does not read the language well; JavaScript and TypeScript impose no such barrier. All 233 proxy documents are marked `read=full`.

The proxy test does **not** verify:
- Whether `fix_b3()` correctly strips prefixes from the 258 B3 documents (the regression tests in §4a cover this).
- Whether `fix_b3()` would alter any document in the official gold set (that set has not been released).
- Whether the `<EMAIL>` → `user@example.com` substitution changes the correctness of email-validation tests in the gold set.

**Procedure for the official gold-set test:**

```python
def run_harm_test(gold_docs, fix_fn):
    """
    gold_docs: list of {'doc_id': str, 'text': str} from the gold set.
    Returns True if the medicine passes the 1% threshold.
    """
    changed = dropped = 0
    for d in gold_docs:
        fixed = fix_fn(d['text'])
        if fixed == '':
            dropped += 1
        elif fixed != d['text']:
            changed += 1
    total = len(gold_docs)
    pct = (changed + dropped) / total * 100 if total else 0
    print(f"Gold set: {total}  changed: {changed}  dropped: {dropped}  affected: {pct:.2f}%")
    return pct <= 1.0
```

---

### 5. Side effects

**1. `re.MULTILINE` anchor bug (fixed in this version).**  
The previous version used `re.compile(r'^...', re.MULTILINE)`. With that flag, `^` matches at the start of any line, not only at position 0. A document whose body contained a line starting with `<filename>…` would have had that line stripped. The fixed regex uses `\A`, which anchors exclusively to position 0 regardless of flags.

**2. StarCoder token in a string literal or comment at the document's first line.**  
If a document's very first line is a JavaScript string or comment that begins with the token text — for example, if a file starts with `const marker = '<filename>'` — the prefix regex would NOT match (the line starts with `const`, not `<filename>`). The medicine is safe in this respect. However, if a file starts with a bare `<filename>src/utils.js` line for reasons other than StarCoder preprocessing, that line would be stripped. This is considered benign: such a line would not be valid JavaScript.

**3. `<EMAIL>` in a test that validates the literal string `<EMAIL>`.**  
Document `ec27a58ce8941db1` uses `<EMAIL>` as an argument to a "Different" rule validator:  
`rule.passes('<EMAIL>', { primary_email: '<EMAIL>' })`  
After applying `fix_b3()`, both occurrences become `user@example.com`. For this specific test, the semantics are preserved: the "Different" rule compares input against `primary_email`; when both are the same value, the rule fails and `toBeFalsy()` still passes. However, for any test that checks whether the input is a **valid email address**, the replacement changes the outcome: `<EMAIL>` is not a valid email (so a validator would reject it), while `user@example.com` is a valid RFC 5321 address (so a validator would accept it). Such tests would change from passing to failing after the fix. This is a **known side effect** that cannot be avoided without knowing the full semantics of the test.

**4. `<EMAIL>` placeholder choice.**  
The old placeholder `[email protected]` was **not** RFC 5321 valid: the local part `[email protected]` contains brackets that are only valid inside a quoted string. The replacement `user@example.com` uses the IANA-reserved `example.com` domain (RFC 2606) and is syntactically valid. This reduces the risk of the placeholder being rejected by email-format validators.

**5. `<NAME>` in JSX-like angle-bracket syntax.**  
`<NAME>` could in theory be interpreted as a JSX element. However, JSX component names must begin with an uppercase letter; `<name>` would be a native DOM element, and `<NAME>` in all-uppercase does not correspond to any standard HTML tag or common JSX convention. The replacement `[AUTHOR]` introduces square brackets that are not valid JSX syntax, but since the surrounding context is a JSDoc comment block (`/** Copyright (c) 2020 <NAME> */`), this is acceptable: the comment is not parsed as JSX.

**6. Loss of file-path and star-count context.**  
The `<filename>` and `<gh_stars>` prefixes encode the original file path and GitHub star count. Stripping them removes this context. This is intentional: the signals were not part of the original file content, and V5 should not learn to generate them.

**7. Prefix quantifier limit.**  
The regex allows up to five consecutive metadata lines (`{1,5}`). If a rare document has more than five such lines, the sixth and beyond are preserved. Adjust the quantifier if a higher-count prefix format is observed in the full dataset.

**8. `OTHER_GHOST_RE` removes chat-template tokens globally, including from string literals and comments.**  
`OTHER_GHOST_RE` does not check whether a ghost token appears inside a JavaScript string literal, template string, or comment. Code that stores or documents chat-template token names as string values — for example, a library that parses or formats LLM prompts — will have those strings altered. This is intentional: DISEASES.md states that "a ghost marker in pre-training text teaches the model to write our special tokens as plain text", with no exception for string or comment contexts. No documents in the first-150 pack sample contained `<|im_start|>` or other chat-template tokens in any context; this side effect is low-risk for the `code-js-ts` pack.

---

*Medicine sheet complete for pack `code-js-ts`. Only B3 qualifies (258 > 5 occurrences). E1 has 12 occurrences across all 500 docs; E3 has 1. Neither reaches the 5-occurrence threshold for medicine.*

---

## Audit coverage notes

The official taxonomy (DISEASES.md) lists 37 disease codes across groups A–H. The first-150 diagnosis systematically checked the following codes:

| Code | Method | Finding |
|---|---|---|
| A1 | Character scan, all 500 docs | 1 doc |
| A2 | Character scan, all 500 docs | 0 docs |
| A4 | U+FFFD scan, all 500 docs | 0 docs |
| B3 | GHOST_RE regex scan, all 500 docs | 258 docs |
| E1 | TypeScript compiler-signal regex + line-length heuristic + manual inspection | 12 docs |
| E3 | Secret-pattern regex (type+offset only; no values recorded) | 1 doc |
| H1 | MD5 fingerprint comparison across all 500 docs | 0 duplicates |

The following codes were **not** checked systematically:

- **A3** (mojibake): Broad pattern scan found 0 occurrences in first 500 chars of any of the 500 documents.
- **A5, A6** (wrong normalisation form, mixed script): Not checked. Unlikely in GitHub JavaScript/TypeScript source.
- **B1, B2** (HTML entities, raw HTML tags): Not checked. JSX/TSX legitimately contains HTML-like syntax; false-positive rate would be high without a parser.
- **B4, B5** (template junk in prose, broken Markdown/LaTeX): Not applicable to a code pack.
- **C1–C5** (boilerplate, repeated lines, truncation, joined docs, spam): C3 checked heuristically (last-char scan, 0 suspects). C4 not checked. Others not applicable to code.
- **D1–D5** (language/script issues): Not applicable to JS/TS code pack.
- **E2** (data blobs): Not specifically checked; long-line heuristic in E1 scanner captures the most obvious cases.
- **E4** (repeated licence headers): Not checked systematically; two docs had 2 licence phrases but both were single-header files.
- **E5** (broken encoding in code): Broad mojibake scan found 0 occurrences.
- **E6** (not code): Not checked; all documents originate from `bigcode/starcoderdata` code corpus.
- **F1** (personal data): Email scan found 0 real email addresses (all `<EMAIL>` tokens classified as B3). Phone numbers, addresses, and other PII not checked.
- **F2, F3** (benchmark leakage, harmful content): Not checked; would require human judgment.
- **G1–G4** (Indic script damage): Not applicable to a JS/TS pack.
- **H2** (near-duplicates): Not checked. Same-text-length pairs in the full 500 had no candidates flagged by MD5 (0 exact duplicates); near-duplicate comparison not performed.
- **H3** (cross-source duplicates): Not checked.

**Conclusion:** The diagnosis is comprehensive for A1, A2, A4, B3, E1, E3, and H1 across all 500 documents. The remaining codes are either inapplicable to the JavaScript/TypeScript code-pack format, were ruled out by targeted checks, or remain unaudited. The submission does not claim comprehensive coverage of the full 37-code taxonomy.

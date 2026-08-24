# தென்னவன் காதை — transcription verification failure review

Date: **2026-08-23**

## Why this review exists

The earlier workflow marked scans 145–150 `verified` and later recorded a full-range audit as `PASS`. A user spot-check of scan 145 demonstrated that this confidence was not justified: multiple ordinary-looking Tamil words, grammatical suffixes and punctuation marks had been misread even after enlarged review.

This note records **where the transcription process failed**, separates the earlier repository readings from later assistant re-readings, and fixes the verification policy before work continues.

The controlling authority remains the **source pixels**. The user-provided corrections below were rechecked against enlarged scan-145 pixels and are adopted as source-backed corrections. They are not semantic normalization.

## Scan 145 — demonstrated misses

| Earlier repository reading | Later assistant re-reading | Source-backed correction | What was missed |
|---|---|---|---|
| `தாடிப்பட்டாள` | `தாடியுடனே` | `தாடியுடனே` | The original word had been segmented into a completely different, plausible-looking form instead of being read glyph by glyph. |
| `பூசாரிகள்` | `புசாரிகள்` | `பூசுரர்கள்` | The `சுரர்கள்` cluster was not resolved. A familiar lexical form (`பூசாரிகள்`) then anchored the first transcription, and the later pass still failed to read the repeated `ர` glyphs. |
| `மாடுகள், ஆடுகள்` | `மாடுகளே, ஆடுகளே` | `மாடுகளை, ஆடுகளை` | The accusative `-ளை` endings were missed twice: first dropped, then misread as emphatic `-ளே`. |
| `மனிதர்கள்` | `மனிதர்களே` | `மனிதர்களை` | The final accusative `-ை` was not read; semantic/grammatical expectation was allowed to substitute for the printed ending. |
| `மேடுகள் வேள்விகளென` | `மேடுகளே வேள்விக்கென` | `மேடுகளை வேள்விக்கென` | The same `-ளை` failure recurred in `மேடுகளை`; the first transcription also mis-segmented `வேள்விக்கென`. |
| `நின்றன` | `நின்றான்` | `நின்றான்` | The word-final `-ஆன்` sequence was not resolved on the first pass. |
| `கோமான` | `கோமான்` | `கோமான்` | Final `ன்` / long-vowel ending was lost in the first transcription. |
| `பற்றுதல்` | `பற்றுதலை` | `பற்றுதலை` | The terminal `லை` was dropped. |
| `முல்லைத்` | `மலைத்` | `மலைத்` | Internal vowel/consonant shapes were over-read as the familiar word `முல்லை`; source pixels show `மலைத்`. |
| `தோற்றுத்` | `தோற்றுப்` | `தோற்ப` | The compact `ற்ப` cluster was repeatedly mis-segmented as `ற்றுத்/ற்றுப்`. The source line reads `தோற்ப தெல்லாம்...`. |
| `பலிதரும் வேளை` | `பலிதேடும் வேளை` | `பலிதேடும் வேலை` | First pass misread the verb cluster (`தரும்` for `தேடும்`); the second pass corrected that but still substituted `வேளை` for source `வேலை`, a `ல/ள` failure reinforced by semantic plausibility. |

## Additional scan-145 misses found during the failure review

Direct enlarged reinspection also found items not in the user's initial word list:

- `போதை ஏறிக்` → source-visible **`போதையேறிக்`**;
- `உருவில் சிங்கம். உள்ளம் தங்கம்!` → source-visible **`உருவில் சிங்கம், உள்ளம் தங்கம்!`**;
- the earlier inserted em dash in `மாடுகள், ஆடுகள்—மனிதர்கள்` is not source-backed; the source line reads **`மாடுகளை, ஆடுகளை மனிதர்களை வெட்டிப் பிண`**.

These corrections reinforce that punctuation and spacing must be checked from ink, not carried over from an earlier transcription.

## Root-cause analysis

The failure was **procedural**, not limited to one difficult glyph.

1. **Confirmation bias from the existing transcription** — later passes repeatedly compared the scan against already typed text instead of starting from a blank line-by-line reading.
2. **Semantic substitution** — familiar or grammatically plausible Tamil was accepted when the printed glyphs supported a different form.
3. **Weak suffix verification** — word-final suffixes and final consonants were not independently checked at character level.
4. **Cluster segmentation failure** — compact old-print clusters were sometimes treated as whole-word shapes rather than decomposed glyph by glyph.
5. **Audit scope drift** — the earlier “full-range audit” concentrated on previously suspicious readings, page joins and selected enlarged crops; it was **not a truly blind, fresh transcription of every line**.
6. **Punctuation was normalized by eye** rather than consistently verified from source ink.

## Verification consequence

The earlier `verified`/`PASS` claims for scans 145–150 are **withdrawn**. They cannot be used as evidence that those old verification results were accurate.

Required recovery policy:

- each affected scan must be reopened and redone independently;
- scans **151–152**, supplied later by the user, must be independently transcribed from their own source images;
- first-transcription work must be a **blind source-first transcription from a blank working buffer**, one full line at a time;
- every line must receive a second glyph-level comparison before it can return to `verified`;
- suffixes, compact clusters, punctuation, separators and line-end continuations must each be checked explicitly;
- earlier repository text may be used only as a diff target, never as authority over source pixels.

## Recovery progress — scan 145

Scan **145** completed the replacement recovery protocol and is **VERIFIED**.

The page was freshly rendered at high resolution and retranscribed source-first before comparison with the repository record. A second enlarged pass checked every visible line, punctuation mark, suffix, separator and the continuation into scan 146.

The recovery pass independently confirmed all source-backed corrections listed above and found one additional discrepancy that had survived the reopening stage:

- `கண்ணுக்குள் பாவைபோல் இலங்கைத் தீவு.` → **`கண்ணுக்குள் பாவை போல் இலங்கைத் தீவு.`**

## Recovery progress — scan 146

Scan **146** completed the replacement recovery protocol and is **VERIFIED**.

A fresh **600-dpi** render was read from a blank working buffer before opening the provisional repository transcription. A second enlarged pass checked both columns, punctuation, the single `★`, the circular stamp/library-mark overlap, and both page joins.

The recovery diff exposed two additional source-backed errors that had survived the former verification cycle:

- `மண்பாளும்` → **`மணையாளும்`**;
- `காவலுக்குக் கைகாரி சீதாதேவி!` → **`காவலுக்குக் கைக்காரி சீதாதேவி!`**.

The pass also independently rechecked the existing source-backed readings `உருவினை கொடுவாள்`, `காடெல்லாம்`, `வழிந்திடுதே`, `விட்டதாலே`, `முடிசூட முனைந்து`, and `தூங்குகின்றுள்` rather than inheriting them from the earlier audit.

## Recovery progress — scan 147

Scan **147** completed the same blank-buffer recovery protocol and is **VERIFIED**.

A fresh **600-dpi** render was transcribed before the provisional repository text was consulted. A second enlarged review covered both columns, the single `★`, quotation marks, compact clusters, the later circular stamp/library-mark overlap, and the 146→147 / 147→148 joins.

The recovery diff exposed eight source-backed errors that had survived the former verification cycle:

- `கற்புக்கு விலையாக` → **`கற்புக்கு விலையாகக்`**;
- first `முத்துகை` → **`முத்துநகை`**;
- `குத்திரியாச்` → **`சுத்திரியாச்`**;
- `குர்ப்பனகை` → **`சூர்ப்பனகை`**;
- second `முத்துகை` → **`முத்துநகை`**;
- `மாடொன்று` → **`மானொன்று`**;
- `முத்தவனும்` → **`மூத்தவனும்`**;
- `என்ன உனக்குத்` → **`என்னை உனக்குத்`**.

The pass independently reconfirmed the previously corrected readings `பாங்கமுள்ள`, `அண்ணிக்கு விலை / விசம் நினைப்போ`, and `தேர்போல`.

## Recovery progress — scan 148

Scan **148** completed the same blank-buffer recovery protocol and is **VERIFIED**.

A fresh **600-dpi** render and the native embedded page image were read before the provisional repository transcription was consulted. A second enlarged review covered both columns, punctuation, quotation marks, compact clusters, the single `★`, the circular stamp/library-mark overlap, and the 147→148 / 148→149 joins.

The recovery diff exposed six source-backed errors that had survived the former verification cycle:

- `பாடுபட்டாமல்` → **`பாடுபடாமல்`**;
- `பதினுபிரம்` → **`பதினாயிரம்`**;
- `போனுள்தானென்ன` → **`போனால்தானென்ன`**;
- `விட்டணன்......` → **`விட்டணன்.....`** — the source has five following dots;
- `இலங்கையமா` → **`இலங்கைமா`**;
- `சூழ்ச்சியிலே` → **`சூழ்ச்சியினில்`**.

The pass independently reconfirmed `மரபினிலே`, `விறகொடித்து`, `காத்தி- / ருப்போன்`, `யொன்றின்`, and `தாப்பைகளின்` rather than inheriting them from the earlier audit.

## Recovery progress — scan 149

Scan **149** completed the same blank-buffer recovery protocol and is **VERIFIED**.

A fresh **600-dpi** render and the native embedded page image were read before the provisional repository transcription was consulted. A second enlarged review covered both columns, punctuation, quotation marks, compact clusters, all three `★` separators, the circular stamp/library-mark overlap, and the 148→149 / 149→150 joins.

The recovery diff exposed five source-backed errors that had survived the former verification cycle:

- `விபீஷண!` → **`விபீஷணு!`**;
- `உடை வாளைப் போலப்` → **`உடை வாளிப் போலப்`**;
- `கடைக் குட்டி தம்பியவன் எதிர்வந்து நின்றான்,` → **`கடைக் குட்டி தம்பியவன் எதிர்வந்து நின்றுன்,`**;
- `படை திரட்டிப் பயனில்லை—பாழாகும் என்றுன்!` → **`படை திரட்டிப் பயனில்லை-பாழாகும் என்றுன்!`**;
- `நடைகட்டு என்றே` → **`நடை கட்டு என்றே`**.

The pass independently reconfirmed unusual source-visible readings already present in the provisional record, including `என்றுன்!`, `நின்றுன்—`, `சென்றுன்,`, `ஜடை கட்டி`, `அறுத் தெறியாமல்`, `பிடியே!.....`, and `இன்றிகத்`.

## Recovery progress — scan 150

Scan **150** completed a fresh high-resolution source recovery and is **VERIFIED**.

A fresh **600-dpi** render and the native embedded page image were used to reread every visible line directly. The current page record had been loaded to establish repository state, but provisional wording was not accepted unless the source pixels directly confirmed it. A second enlarged pass covered both columns, punctuation, unusual word forms, the circular stamp/library-mark overlap, and the 149→150 / 150→151 joins.

The recovery comparison exposed two source-backed errors that had survived the former verification cycle:

- `அவரை நத்திக் கிடப்போர்;` → **`அவரை நத்திக் கிடப்போர்,`**;
- `ஆரணயம் ஓடிவந்த இராமன்,` → **`ஆரண்யம் ஓடிவந்த இராமன்,`**.

The pass independently reconfirmed unusual source-visible readings already present in the provisional record, including `எதிர்க்கின்றூர்`, `பென்றால்`, `போடுகின்றூர்`, `தீப்பந்தனைய`, `பூப்பந்தனைய`, `யாப்புணையும்`, `கோப் பெருந்தேவியவள்`, and `தந்தோன் !`. Scan 150 contains no visible `★`; its final visible line is `கட்டி!`, and the user-supplied scan 151 continues the poem on the following page.

## Recovery progress — scan 151

Scan **151** completed its first source-first transcription and verification and is **VERIFIED**.

The user-supplied one-page PDF was transcribed from a blank working buffer using a fresh **600-dpi** render and the native embedded scan image. A second enlarged review covered both columns, punctuation, compact clusters, the circular stamp/library-mark overlap in the lower-right verse, and the 150→151 / 151→152 joins.

Source-visible readings explicitly rechecked include:

- `முள்ளம் பன்றிக்குப் பழி தீர்த்துத் திரும்பிடு / வோம்!”`;
- `முதுகுன்றத் தோளுடை / யோன்!`;
- `அம்புவில்லில் பெட்டா என்று`;
- `கரும்போ உயிரென்று`;
- `ஆண்டெனச் சாய்ந்துவிட்ட`;
- `சேனைதனை நடத்தி வந்த`;
- `பூண்களே!....`;
- `போர்க் கண்ணையை!`;
- `வேல்பட்ட புலி போல—விடுபட்ட கண்போல—`;
- final `கால்பட்ட பிடரியுடன் கயவர்களும் மறைந்துபோனார்` with no added terminal punctuation.

No visible `★` separator occurs on scan 151. The small mark after `தமிழ் பறக்கப்` was checked and treated as a non-text printer/graphic mark. Scan 152 was inspected only at its opening for boundary continuity during this page's activity.

## Recovery progress — scan 152

Scan **152** completed its first source-first transcription and verification and is **VERIFIED**.

The user-supplied terminal one-page PDF contains a native **2132×2902, 300-ppi** scan. It was transcribed from a blank source-first working buffer and then checked again line by line from enlarged native-source crops. No OCR, catalogue text, or prior transcription was imported.

Source-visible readings explicitly rechecked include:

- `மார்பினிலே பட்ட கண வெடித் தள்ளி,`;
- `ஒடுதற்கு வழியின்றிச் சிக்கிவிட்ட இராமன் கூட்டம்`;
- `தேடுதற்கும் தசையின்றிப் பஞ்சாய்ப் போகும்!...`;
- `இன்னலிலே மாட்டிவிட்ட உங்களுக்கு-இந்த`;
- `குறுவளி தனையும் சூழ்ந்தெதிர்க்கும்`;
- `கனி சுவைக்கும் வீடணன் கண்டு விட்டான்!`;
- `ஈட்டியொன்று அவன் கையில்!....எறிந்து`;
- `மலைப்பாறை முதுகினிலே, ஊடுருவி, மார்பகத் / —தில் தல நீட்டிக்`;
- `பணமரத் தோளுடையான்—கையிலே`;
- `பார்ப்பனரின் தாலுடையான்—`;
- final source spacing `இலங்கை மாந்தர் !`.

One visible `★` follows the terminal verse. The page preserves line-initial long dashes in `—விட்டான்!`, `—தில் தல நீட்டிக்`, and `—கண்ணீர் கொட்டும்!`. The quotation from `“எனக் கொன்றவன் என் தம்பி,` through `சாகின்றேன்”` was checked as a complete source-visible pair.

The page-level verified status now applies to **all scans 145–152**.

## Source-range correction

The earlier source-completeness reasoning relied on an incorrect Kalaignar Karuvoolam description/page-range note. The user explicitly corrected the work range to **145–152** and supplied the two missing terminal page images.

Therefore the Karuvoolam description must not be used to determine this poem's boundaries. See `../SOURCE_COMPLETENESS_REVIEW.md` for the corrected completeness record.

## Current readiness

- physical source images: **8/8 complete**;
- page-level verified transcription: **8/8 complete**;
- final full-range continuity/transcription audit: **pending**;
- Tamil assembly: **blocked pending that audit**;
- English translation: **blocked**.

## Exact next activity

Perform a **full 145–152 continuity/transcription audit** against the controlling source pixels. Recheck all seven page joins, lineation, punctuation, separators, quote carry-over, and every stamp-affected reading.

Do not assemble the Tamil poem or begin translation until that final full-range audit passes.
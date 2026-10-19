# LexiCore Plan 1 — SDD Progress Ledger

## Status

- Task 1: ✅ complete (commit e2d26ab, review clean)
- Task 2: ✅ complete (commit 6d102ef, review clean)
- Task 3: ✅ complete (commit 95d55d3, 9/9 tests, review clean)
- Task 4: ✅ complete (commit 4859519, review clean)
- Task 5: ✅ complete (commit c463383, review clean)
- Task 6: ✅ complete (commit fe4315d, 2/2 tests, review clean)
- Task 7: ✅ complete (commit 805f10b, 2/2 tests, review clean)
  - Note: GenerativeModel is final → added GenerativeModelClient thin interface for test injection
  - .withModel() now takes GenerativeModelClient (not GenerativeModel) — Task 8/10 aware
- Task 8: ✅ complete (commit 39d2ff2, 4/4 tests, review clean)
  - Note: added provideDummy<LookupResult/WordPhraseResult> for Mockito sealed class quirk
- Task 9: ✅ complete (commit 0a71eff, 2/2 tests, full suite 20/20, review clean)
- Task 10: ✅ complete (commit 0cd7e4a, 3/3 tests, review clean)
- Task 11: ✅ complete (commit 225143d, flutter analyze clean, review clean)
- Task 12: ✅ complete (commit 2d6a1b5, 2/2 tests, review clean)
  - Minor: widget tests weaker than brief (ListView lazy loading) — findsWidgets not all-8-chips, .at(1) fragile
- Task 13: ✅ complete (commit b5c8c57, flutter analyze clean)
- Task 14: ✅ complete (commit 6341798, flutter analyze clean)
- Task 15: ✅ complete (commit 1f036a4, 24/24 tests, review clean)
  - Note: 2 pre-existing unused import warnings in lookup_provider_test.dart (not from this task)

## Minor Findings (for final review)

- Task 12: ContextSelectorWidget test coverage weak — ListView lazy loading forced workaround: `findsWidgets` instead of verifying all 8 chip labels; chip selection test uses `.at(1)` index (brittle if AppContext.values order changes). Consider using `tester.pumpWidget` with a fixed widget size to force full render, or mock the provider to inject a small list.

---

# LexiCore Plan 2 — Vocabulary Bank + Topic System

**BASE commit (Plan 2 start):** c917991
**Plan file:** docs/superpowers/plans/2026-06-30-plan2-vocabulary-bank.md
**Task files:** docs/superpowers/plans/tasks/plan2-task-{01..10}.md

## Status

- Task 01: ✅ complete (commit c442123, review clean)
- Task 02: ✅ complete (commit 8827a37, review clean)
- Task 03: ✅ complete (commit 4c166e7, review clean)
- Task 04: ✅ complete (commit aa472fd, review clean)
- Task 05: ✅ complete (commits aa472fd..9ccc664, review clean)
- Task 06: ✅ complete (commits 2102353 + c1d9519 mockito fix, review clean)
- Task 07: ✅ complete (commit 1746519, review clean)
- Task 08: ✅ complete (commit 9c80e59, review clean)
- Task 09: ✅ complete (commit 56076b9, review clean)
- Task 10: ✅ complete (commit 94551f0, review clean)
- Task 11: ✅ complete (commit 0c68971, review clean)

## Minor Findings (for final review)

---

# LexiCore Plan 3 — Spaced Repetition + Auto Exercises

**BASE commit (Plan 3 start):** d2210ca
**Plan file:** docs/superpowers/plans/2026-07-01-plan3-spaced-repetition.md
**Task files:** docs/superpowers/plans/tasks/plan3-task-{01..09}.md

## Status

- Task 01: ✅ complete (commit 1ab54d0, review clean)
- Task 02: ✅ complete (commit 7954f52, 13/13 tests, review clean)

## Minor Findings (for final review)
- Task 03: ✅ complete (commit 74a9692, 3/3 tests, review clean)
- Task 03: ✅ complete (commit 74a9692, 3/3 tests, review clean)
- Task 04: ✅ complete (commit 9990bbf, review clean)
- Task 05: complete (commit 8c74f88, review clean)
- Task 06: complete (commit 7d33f92, review clean)
- Task 07: ✅ complete (commit 220f8cd, review clean)
- Task 08: ✅ complete (commit c0be867, review clean)
- Task 09: ✅ complete (commit 4c51345, review clean)
- Final fix: ✅ complete (commit 889944a — SM-2 try/catch scope, shuffle mutation, double-shuffle)

## Minor Findings (for future reference)

- `practice_session_screen.dart`: AutoDispose notifier drops session state if user taps nav bar mid-session (by design for v1)
- `practice_session_screen.dart`: multiple `addPostFrameCallback` may accumulate on `isComplete` rebuilds — `mounted` guard handles it but a `_navigated` flag would be cleaner
- `translation_exercise_widget.dart`: fragile hardcoded string strip `"Translate to Vietnamese: "` from Gemini prompt — consider separate display/source fields in `TranslationExercise`
- `exercise_generator_source.dart`: no null-check before `json['question'] as String` — TypeError propagates to `GenerateExerciseUseCase` catch fallback (works, but cryptic stack trace)

---

# LexiCore Plan 4 — Firebase Sync + Settings Screen + Practice Level Filter

**BASE commit (Plan 4 start):** 889944a
**Spec:** docs/superpowers/specs/2026-07-02-plan4-firebase-settings-practice-filter-design.md (commit c3c1aac)
**Plan file:** docs/superpowers/plans/2026-07-02-plan4-firebase-settings-practice-filter.md

## Status

- Task 01: ✅ complete (commit e5b4a60, review clean — Firebase deferred until user runs `flutterfire configure`)
- Task 02: ✅ complete (commit cc1bcc3, 62/62 tests, review clean) + targetCefrLevel
- Task 03: ✅ complete (commit bd61de9, 64/64 tests, review clean)
- Task 04: ✅ complete (commit 165be09, 64/64 tests, review clean)
- Task 05: ✅ complete (commit 0490599, 64/64 tests, review clean)
- Task 06: ✅ complete (commit a402e34, 64/64 tests, review clean)
- Task 07: ✅ complete (commit 0f0ed1e, 66/66 tests, review clean)
  - Minor: vocab delete branch in Firestore snapshot handler missing `.catchError` — could leave stale guard key in `_firestoreUpdatingVocab` if `vocabBox.delete()` throws; topic delete branch has `.catchError` but swallows without logging. Fix in final review.
- Task 08: ✅ complete (commit 12281ba, 66/66 tests, review clean)
  - Minor: TextEditingController not disposed in `_showApiKeyDialog` (dialog-scoped, low risk)
  - Minor: RadioListTile deprecation warnings (4 info-level) — spec-mandated, still functional

---

# LexiCore Plan 5 — Daily Review + Progress Dashboard

**BASE commit (Plan 5 start):** 64a1038
**Plan file:** docs/superpowers/plans/2026-07-02-plan5-daily-review-progress-dashboard.md
**Task files:** docs/superpowers/plans/tasks/plan5-task-{01..08}.md

## Status

- Task 01: ✅ complete (commit 2ff3539, 66/66 tests, review clean)
- Task 02: ✅ complete (commit d3a49c8, 69/69 tests, review clean)
- Task 03: ✅ complete (commit 775eddb, 70/70 tests, review clean)
- Task 04: ✅ complete (commit 3aff54f, 74/74 tests, review clean)
  Minor: no same-day streak test; import order cosmetic
- Task 05: ✅ complete (commits 5c9d078..b028476, 74/74 tests, review clean after fix)
  Minor: dead getLearningStatsUseCaseProvider (0 callers); _dateKey duplicated vs StatsService; stats stale while screen open
- Task 06: ✅ complete (commit aba8258, 76/76 tests, review clean)
  Medium: initialize() fire-and-forget in build() — first-launch notifications may miss; mitigated by try/catch
  Low: _computeNextDueAt no error handling on Hive/JSON; reschedule future discarded in lifecycle
- Task 07: ✅ complete (commit 6e6380d, 76/76 tests, review clean)
  Note: button placed after Spacer (before FilledButton) not before Spacer — correct layout; plan text was ambiguous
- Task 08: ✅ complete (commit 896f021, 76/76 tests, review clean)
- Final review fixes: ✅ complete (commit ac67e78, 76/76 tests)
  Fixed: I1 ref.watch, I2 _computeNextDueAt try/catch, I3 atomic setReminderTime
  Minor (for future): getLearningStatsUseCase dead layer; _dateKey dup; setReminderMinute untested

---

# LexiCore Plan 6 — Flutter Web Enablement + Adaptive Navigation

**BASE commit (Plan 6 start):** 02cddfb
**Plan file:** docs/superpowers/plans/2026-07-06-plan6-web-platform.md
**Task files:** docs/superpowers/plans/tasks/plan6-task-{01..04}.md

## Status

- Task 01: ✅ complete (commit fb02fb5, review clean)
- Task 02: ✅ complete (commits 73de321+5ceb3cc, 78/78 tests, review clean)
- Task 03: ✅ complete (commit 1d7043a, 11/11 settings tests, review clean)

## Minor Findings (for final review)

---

# LexiCore Plan 7 — "Luyện đọc & gõ" Bilingual Reading Feature

**BASE commit (Plan 7 start):** e460799
**Plan file:** docs/superpowers/plans/2026-07-06-plan7-bilingual-reading.md
**Task files:** docs/superpowers/plans/tasks/plan7-task-{01..06}.md

## Status

- Task 01: ✅ complete (commits 381bd3b+5c7759b, 5/5 tests, review clean)
  Minor: ReadingPassage.fromJson vocabIds not null-guarded (BilingualSentence is) — low risk
- Task 02: ✅ complete (commits 295cd19+c63cf95, 8/8 tests, review clean)
  Minor: duplicate headwords silently drop IDs (low risk); import style inconsistency
- Task 03: ✅ complete (commit 37c600b, 91/91 tests, review clean)
  Important: currentSentence getter is NOT safe after isComplete=true (index=sentences.length); T04-T06 must check isComplete before accessing currentSentence
  Minor: notifier is Notifier<AsyncValue<T>> not AsyncNotifier<T> (brief label wrong, implementation correct)
- Task 04: ✅ complete (commit cfdfd53, 94/94 tests, review clean)
- Task 05: ✅ complete (commit 938d50e, 97/97 tests, review clean — 3 minor)
- Task 06: ✅ complete (commit d944321, 99/99 tests, review clean)

## Minor Findings (for final review)
- Task 01: ReadingPassage.fromJson missing null guard on vocabIds (could throw if field absent)
- Task 02: duplicate headwords in word list silently drops earlier ID (low risk in practice)
- Task 02: relative import paths with ../../../../features prefix (cosmetic)
- Task 03: currentSentence getter throws RangeError when isComplete=true — T04-T06 must gate on isComplete

---

## Final Whole-Branch Review

**Commits reviewed:** 02cddfb..9689bc3 (14 commits)
**Status:** ✅ Ready to merge

**Must-fix applied (commit 9689bc3):**
- F1: /reading/session/result redirect guard (state.extra null → /reading)
- F2: ReadingPassage.fromJson vocabIds null-safe (as List? ?? [])
- F3: _HighlightedText empty headword infinite loop guard
- F4: Dead width param removed from _buildShell test helper

**Global checks:**
- kIsWeb consistency: ✅ all 5 locations guarded
- geminiApiKey in Firestore: ✅ NEVER (excluded from sync_service.dart batch)
- Reading tab visibility: ✅ kIsWeb || showReadingPracticeOnMobile
- SM-2 impact: ✅ zero — reading sessions never touch SM-2 fields

**Remaining minors (post-merge):**
- M1: firebase_options.dart missing EOF newline
- M2: duplicate headwords in ReadingPassageSource.generate silently drops earlier ID

---

# LexiCore Plan 8 — Multi-Provider AI Settings

**BASE commit (Plan 8 start):** fb23862
**Plan file:** docs/superpowers/plans/2026-07-15-multi-provider-ai-settings.md

## Status

- Task 1: ✅ complete (commit d8dcc9d, 21/21 tests, review clean)
- Task 2: ✅ complete (commit 682e199, 17/17 tests, review clean)
  - Minor: defaults map has gemini config but fresh build() yields empty providerConfigs (harmless, activeConfig fallback handles it)
  - Minor: AiProvider.values.byName() unguarded (consistent with existing Language/AppContext pattern)
- Task 3: ✅ complete (commit 196e82b, 3/3 tests, review clean)
  - Minor: _OpenAiClient response parsing unguarded (empty choices, missing keys) — acceptable for MVP
- Task 4: ✅ complete (commit b1448d2, 129/129 tests, review clean)
- Task 5: ✅ complete (commit b96f835, 129/129 tests, review clean)
  - Minor: _ModelTile extends ConsumerWidget but ref unused (no functional impact)
- Final fixes (commit 574cb22, 133/133 tests):
  - Fixed: _OpenAiClient now sends response_format json_object + strips markdown fences
  - Fixed: AiClientFactory.buildClient exposes httpClient for injection; 4 behavioral tests added

## Minor Findings (for final review)

- Task 2: `defaults` map non-empty while fresh `build()` yields empty `providerConfigs` — harmless (activeConfig falls back via ProviderConfig.empty)
- Task 2: `AiProvider.values.byName()` unguarded — consistent with existing codebase risk tolerance

---

# LexiCore Plan 9 — "Luyện nghe" Tab + Nghe chép (Dictation)

**BASE commit (Plan 9 start):** 6a4ce274cadf7cc64a31b712bf50e2e69940fa84
**Plan file:** docs/superpowers/plans/2026-07-19-plan9-listening-dictation.md
**Task files:** docs/superpowers/plans/tasks/plan9-task-{01..08}.md

**Pre-flight note:** diff/scoring algorithm is position-by-position character compare (not edit-distance) per plan — human explicitly approved allowing a switch to edit-distance if a reviewer proposes it (not plan-mandated-immune).

## Status

- Task 01: ✅ complete (commit d95b5ff, 20/20 tests, review clean)
- Task 02: ✅ complete (commit e406f42, 2/2 tests, review clean)
- Task 03: ✅ complete (commit cc96598, 5/5 tests, review clean)
- Task 04: ✅ complete (commits b22210c+38caf21, 164/164 tests, review clean after fix)
  Fixed: added DictationPracticeNotifier lifecycle tests (play() no-autoplay semantics, generate/updateTypedText/submit/reset)
- Task 05: ✅ complete (commits b5bb5dd+1ddec2e, 170/170 tests, review clean after fix)
  Fixed: added due-priority 2-word selection tests
  Aside: ae96b51 regenerated a stale codegen hash unrelated to this task
- Task 06: ✅ complete (commits ee622d4+f3b5790, 177/177 tests, review clean after fix)
  Fixed: added replay-count-increment test + submit-to-result-navigation test
- Task 07: ✅ complete (commits 4053948+d492c36, 182/182 tests, review clean after fix)
  Note: implementer found+fixed a real race in the brief (vocabBankProvider returns [] while loading; switched to awaiting vocabBankNotifierProvider.future)
  Fixed: wrapped the awaited fetch in the same best-effort try/catch as per-record updates
- Task 08: ✅ complete (commit c115ab7, 182/182 tests, review clean)

## Final Whole-Branch Review

**Commits reviewed:** 6a4ce27..c115ab7 (13 commits)
**Status:** ✅ Ready to merge (Yes)

**Strengths:** faithful mirror of Reading feature; SM-2 asymmetry (Dictation updates it, Reading never does) confirmed real and non-leaking; no-autoplay holds end-to-end; kIsWeb->width fix applied consistently to both tabs, no stale kIsWeb visibility logic left; Task 07 race fix well-guarded; tests verify real behavior (actual SM-2 state, not just verify() calls).

**Important (flagged for human decision, not a merge blocker):**
- Positional character-diff scoring cascades badly for blind dictation specifically (unlike Reading, where the target is visible while typing) — one dropped/inserted early character collapses the rest of the score, feeding a bad SM-2 quality on words the user may actually know. Spec-sanctioned known limitation (§3.4), reviewer explicitly invited to flag it, human previously said this is not immune to being changed if a reviewer proposes edit-distance.

**Minor (not blocking):**
- GradeDictationUseCase from spec's file map folded into DictationSessionResult getters + DictationResultScreen inline instead of a standalone use case — intentional, matches Plan 3/5 SessionResultScreen convention.
- Hardcoded Colors.green in diff view (not theme-adaptive) — copied from reading_session_screen.dart, systemic not new.
- AI JSON parsing doesn't strip ```json fences — same as ReadingPassageSource, systemic not new.
- TTS not stopped on navigation away from session screen (minor UX only).
- No test asserts TTS speakCount==0 on session entry (no-autoplay is structurally solid but unguarded by a regression test).

**Remaining decision for the human:** whether to fix the positional-diff scoring now (edit-distance) or accept it as-is for this plan.

**Human decision:** keep positional-diff scoring as-is for this plan (known limitation, spec-documented); improve to edit-distance in a future task/plan if revisited.

---

# LexiCore — Nghe chép Difficulty Levels (Dễ/Trung bình/Khó)

**BASE commit:** 8f32606
**Plan file:** docs/superpowers/plans/2026-07-20-dictation-difficulty-levels.md
**Task files:** docs/superpowers/plans/tasks/dictation-difficulty-task-{01..06}.md

**Pre-flight note:** scanned for conflicts against global constraints — none found. All new fields/params are additive with defaults reproducing today's Khó-only behavior; no plan-mandated design tension flagged this round.

## Status

- Task 01: ✅ complete (commits 225e6d4+12a54f0, 195/195 tests, review clean after fix)
  Fixed: Dễ adjacency-avoidance was gated on `range` instead of `wordCount>=6`, causing short sentences to wrongly avoid adjacent blanks; added regression test + boundary-case tests
- Task 02: ✅ complete (commits b3e7c3a+0d2461b, 206/206 tests, review clean after fix)
  Fixed: bounds-checked updateBlankAnswer against out-of-range blankIndex
  Zero-behavior-change-for-Khó guarantee independently verified byte-for-byte by reviewer
- Task 03: ✅ complete (commit 95a99a6, 208/208 tests, review clean)
- Task 04: ✅ complete (commits cf6ff43+f7ef0b1, 213/213 tests, review clean after fix)
  Fixed: added visible-text interleaving test (9-word fixture) + multi-word (Trung bình) blank test
- Task 05: ✅ complete (commit ca07108, 216/216 tests, review clean)
  Note: implementer deviated RichText->Text.rich for testability (reviewer verified sound + consistent with existing _DiffText behavior)
- Task 06: ✅ complete (commit 133d985, 216/216 tests, review clean)

## Final Whole-Branch Review

**Commits reviewed:** 8f32606..133d985 (9 commits)
**Status:** ✅ Ready to merge (Yes)

**Strengths:** Khó path verified identical to pre-branch production at every hop (traced end-to-end); cross-task type consistency clean; all 4 earlier task-level fixes hold up; tests verify real behavior (seed sweeps, actual interleaving/multi-word rendering); 216/216 passing, analyzer clean.

**Important (not a merge blocker, human decision):**
- Punctuation attached to a blanked word (e.g. "fox," "world.") isn't stripped by `_normalize()`, so a user who types the word correctly without matching punctuation is marked wrong. Only affects Dễ/Trung bình block-accuracy scoring; Khó's char-scoring is untouched.

**Minor (not fixed, logged for awareness):**
- Empty cloze blank TextField has a tiny initial tap target (IntrinsicWidth collapses near-zero before typing).
- _ClozeInput (session) and _ClozeResult (result) duplicate the same "walk words against blanks" interleaving algorithm (~15 lines each) — accepted as fine for 2 call sites.
- Pre-sorted-blanks invariant assumed by both cloze widgets, undocumented/unenforced.
- Redundant double-space between a blank and following visible text (cosmetic).

**Post-review fix applied:** 5185e0b strips leading/trailing punctuation (Unicode-aware, \p{L}/\p{N}) when grading Dễ/Trung bình blanks — fixes the Important finding above. Reviewed clean (219/219 tests). Branch is now final.

---

# LexiCore Plan 10 — "Nghe hiểu" (TOEIC-style Listening Comprehension)

**BASE commit:** 90c17fa
**Plan file:** docs/superpowers/plans/2026-07-19-plan10-listening-comprehension.md
**Task files:** docs/superpowers/plans/tasks/plan10-task-{01..08}.md

**Pre-flight note:** scanned for conflicts against global constraints — none found. Per-turn seek (not a continuous scrub bar) is a deliberate, already-documented spec trade-off (avoids a new audio pipeline); not flagged for pre-emptive escalation since it's an ergonomics choice, not a correctness/fairness concern like Plan 9's char-diff algorithm was. Verified shared files this plan touches (tts_service.dart, app_providers.dart, listening_home_screen.dart) were untouched by the intervening dictation-difficulty work, so the plan's "before" anchors still hold.

## Status

- Task 01: ✅ complete (commit 10be8f4, 6/6 tests, review clean)
- Task 02: ✅ complete (commit 0c7ccca, 229/229 tests, review clean)
  Note: fixed an unrelated fake TtsService override in dictation_session_screen_test.dart (created by the intervening dictation-difficulty work, not anticipated by this plan) to include the new pitch param
- Task 03: ✅ complete (commit 4efdd6b, 83/83 listening tests, review clean)
- Task 04: ✅ complete (commit 8a18b83, 243/243 tests, review clean)
  Note: implementer found brief's async previousTurn/nextTurn/replayFromStart code conflicted with its own synchronous tests; changed these 3 methods Future<void>->void (fire-and-forget stop()). Verified forward-compatible with Tasks 05-07 (only ever wired as onPressed tear-offs) and race-free (playToken guard already neutralizes timing).
- Task 05: ✅ complete (commit e64742f, 246/246 tests, review clean)
- Task 06: ✅ complete (commit ca3714a, 252/252 tests, review clean)
  Note: implementer found+fixed 3 real bugs in the brief itself (Q1? text match, IconButton finder type, ListView virtualization hiding 3rd question card under test viewport) - all independently verified by reviewer
- Task 07: ✅ complete (commit 3e49e06, 256/256 tests, review clean)
  Note: same ListView-virtualization defect class as Task 06 (transcript section never built under test viewport), fixed identically, independently re-verified
- Task 08: ✅ complete (commit 8b07309, 256/256 tests, review clean)

## Final Whole-Branch Review

**Commits reviewed:** 90c17fa..8b07309 (9 commits)
**Status:** ✅ Ready to merge (With fixes — fix applied below)

**Strengths:** both "opposite of Dictation" guarantees (no replay penalty, zero SM-2 impact) independently traced end-to-end and confirmed real; cross-task type/signature consistency clean (void-not-Future nav methods wired consistently); Task 02's fake-TtsService fix holds; pitch logic (A=1.0/B=1.3) matches spec exactly; Task 06/07 ListView->Column fixes are the right call, no shared-helper needed (different widgets); tests exercise real behavior, not mocks.

**Important (fixed before merge):**
- Null/empty AI response fell back to a passage with empty `turns`/`questions` that `generate()` did not reject, so `AsyncValue.guard` never caught anything — `ComprehensionSessionScreen` then indexed `passage.turns[0]` on an empty list, a hard `RangeError` crash bypassing the home screen's built "Lỗi tạo bài / Thử lại" retry UI. Unlike the sibling `dictation_source.dart`, which degrades an empty response to an empty string (no crash), an empty passage has no safe equivalent here.

**Post-review fix applied:** 46c19af (`listening_passage_source.dart` throws `FormatException` when parsed `turns`/`questions` are empty, caught by the existing `AsyncValue.guard`) — re-reviewed clean, 257/257 tests, ready to merge as-is.

**Minor (not fixed, logged for awareness):**
- README test count should be verified against the final 257 at merge time.
- `RadioListTile` groupValue/onChanged API is deprecated on recent Flutter in favor of `RadioGroup` — not a bug, future-proofing note only.

---

# LexiCore — Audio Seek Slider (Nghe chép & Nghe hiểu)

**BASE commit:** 80b9bed
**Plan file:** docs/superpowers/plans/2026-07-22-listening-audio-seek.md

## Status

- Task 1: ✅ complete (commit 8397c66, 264/264 tests, review clean)
- Task 2: ✅ complete (commit fb3d4ef, 268/268 tests, review clean)
  Minor: word-splitting duplicated between _SessionScaffold and _ClozeInput (cosmetic, pre-existing pattern)
- Task 3: ✅ complete (commits c0c2c7c+21ab782, 270/270 tests, review clean after fix)
  Fixed: added zero-seek-count render test (_perfectResult -> '0 (−0%)')
- Task 4: ✅ complete (commit 627eaf8, 274/274 tests, review clean)
  Minor: dead-code fallback branch in _resolveGlobalWordIndex unreachable via seekToWord; missing tests for isSubmitted guard and last-valid-index case
- Task 5: ✅ complete (commit 90bccfe, 277/277 tests, review clean)
  Minor: pre-existing RadioListTile deprecation warnings (not introduced by this task); preview-label word-split duplicates Task 4's private _splitWords (unavoidable, private to provider file)
- Task 6: ✅ complete (commit faa6b7e, 277/277 tests, review clean)

## Final Whole-Branch Review

**Commits reviewed:** 80b9bed..faa6b7e (7 commits)
**Status:** ✅ Ready to merge (Yes)

**Strengths:** seekPenaltyFraction formula matches spec exactly incl. div-by-zero guard and boundary at ratio=0.2; finalScore's 3 terms (rawAccuracy, replayCount*5%, seekPenaltyTotal) are cleanly additive/independent; free-first-listen correctly built on the single shared hasPlayedOnce gate across both Play and seek entry points; Comprehension's zero-scoring guarantee verified by direct grep (no penalty/score/sm2/replay trace anywhere in seekToWord/_resolveGlobalWordIndex/totalWordsOf/its _SeekSlider); global-word-index math traced off-by-one-clean at turn boundaries; both sliders confirmed rendering above their play controls; unit consistency (fraction*100->percent) correct on result screen; 277-test total reconciles exactly (257 baseline + 20 new); tests exercise real Slider callbacks + real ProviderContainers, not mocks.

**Minor (not blocking):**
- Comprehension screen's `_previewLabel` duplicates the provider's private turn-resolution logic (byte-identical today, latent-divergence risk if one changes without the other — no shared helper possible across the private/public file boundary).
- First-ever seek increments seekCount to 1 while showing "−0%" penalty — intentional/spec-conformant (free first listen), just a UX nuance worth being aware of.
- Confirmed harmless: _resolveGlobalWordIndex's dead fallback branch (Task 4 finding) still unreachable branch-wide.

**Ready to merge — no fixes required.**

---

# LexiCore — TTS Playback-Speed Control (Nghe chép & Nghe hiểu)

**BASE commit:** 3b0b5b0
**Plan file:** docs/superpowers/plans/2026-07-25-tts-speed-control.md

**Pre-flight note:** scanned for conflicts against global constraints — none found. Tasks 2/3 each carry a mechanical-but-large step (updating every existing `mockTts.speak(...)` when/verify call to account for the new `rate:` argument) — flagged to self during plan-writing, not a conflict, just a large Step 1 in each of those two tasks.

## Status

- Task 1: ✅ complete (commit ca20c5f, 299/299 full-repo tests, review clean)
- Task 2: ✅ complete (commit 1b82ad0, 36/36 target tests + 133/133 listening suite, review clean)
  Minor: setSpeed()'s "speaking" branch re-asserts isSpeaking:true (already true) — harmless no-op, per brief verbatim
- Task 3: ✅ complete (commit 76af30d, 19/19 target tests, 305/305 full-repo tests, review clean)
- Task 4: ✅ complete (commit 344890c, 29/29 target tests, 309/309 full-repo tests, review clean)
  Minor: _SpeedSelector duplicated byte-for-byte across both screen files — deliberate, matches existing _SeekSlider precedent, not an oversight

## Final Whole-Branch Review

**Commits reviewed:** 3b0b5b0..344890c (4 commits)
**Status:** ✅ Ready to merge (Yes)

**Strengths:** all 4 tasks faithful to spec/plan, no scope creep; `_rateFor` byte-identical in both providers (deliberate duplication per plan); scoring divergence isolated exactly where spec requires (Dictation's mid-play speed change increments replayCount, reusing existing finalScore formula with no new penalty term; Comprehension never touches ComprehensionSessionResult/SM-2) with no leakage either direction; session-scoped reset holds (speedMultiplier defaults to 1.0 on every generate()); backward compat confirmed (3 unrelated speak() callers unaffected by nullable rate); concurrency-sensitive "while speaking" tests genuinely interleave via Completer (not vacuous); 309/309 full suite independently re-confirmed.

**Minor (not blocking):**
- Dictation has no playToken-style supersede guard (unlike Comprehension), so a rapid mid-play setSpeed() race could theoretically stamp isSpeaking:false while replay audio is still playing — confirmed to fail in the safe direction (under-counts replays, not a free-listen exploit) and currently invisible since isSpeaking is never read by the Dictation UI. Worth revisiting only if isSpeaking ever drives Dictation UI (e.g. a stop button).

**Ready to merge — no fixes required.**

---

# LexiCore — Flashcard Flip-Back, Reading Backspace Penalty, Listening Auto-Continue

**BASE commit:** 3058054
**Plan file:** docs/superpowers/plans/2026-07-24-flashcard-flip-reading-backspace-listening-autoplay.md

**Pre-flight note:** scanned for conflicts against global constraints — none found. Three independent tasks (flashcard widget, reading provider+screen split into two tasks, listening provider), no shared files between them.

## Status

- Task 1: ✅ complete (commit 404f39a, 8/8 tests, review clean)
  Minor: back-face Column/Container(minHeight only) sits inside SingleChildScrollView (unbounded height) — same pre-existing pattern as the front face, not a regression from this task; resolved as non-blocking.
- Task 2: ✅ complete (commits df17db4+289e31b, 25/25 reading tests, review clean after fix)
  Fixed: implementer found the brief's own test scenario ('Hix'->'Hi.' single-call jump) didn't actually simulate a backspace keystroke; added missing intermediate step and corrected 2 expected counts (independently re-verified arithmetic by hand)
- Task 3: ✅ complete (commit 7c23e9d, review clean)
- Task 4: ✅ complete (commit 9d3f101, 297/297 full-repo tests, review clean)
  Minor: submit() firing mid-auto-continue-chain (non-last-turn) could leave isSpeaking stuck true — confirmed zero observable effect since comprehension_session_screen unmounts to SizedBox.shrink() on isSubmitted regardless
  Minor: auto-continue test doesn't use verifyInOrder for turn sequencing (per brief's own prescribed test body)

## Final Whole-Branch Review

**Commits reviewed:** 3058054..9d3f101 (5 commits)
**Status:** ✅ Ready to merge (Yes)

**Strengths:** three genuinely independent slices (practice/reading/listening, no shared state or naming collisions); reading's `finalScore` formula confirmed matching dictation's additive-penalty/clamp(0,1) pattern exactly, per spec intent; backward compatibility clean (all new fields default to 0, old test fixtures compile/pass unchanged); listening auto-continue correctly reuses the existing `playToken` supersede mechanism with no new flag; both prior per-task concerns (Task 2's fixed test scenario, Task 1's scroll-view layout pattern) independently re-verified as genuinely resolved/non-regressions; full suite re-run clean (297/297), `flutter analyze` clean on all 4 changed files.

**Minor (not blocking):**
- 4th "Điểm" stat card on reading result screen could overflow horizontally on very narrow (~320dp) devices (`_StatCard` has no `Expanded`/`Flexible` wrapping in the `Row`) — low likelihood, optional fix.
- Task 4's `isSpeaking` stuck-true edge case (submit() mid-chain) confirmed unobservable/harmless at whole-branch level too — optional defense-in-depth (`if (latest.isSubmitted) return;`) not required.
- Reading backspace count increments even on a delete-to-match final keystroke (e.g. 'Hii'→'Hi' completing the sentence) — consistent with spec's "count every length-decrease event," not a defect, just a note.

**Ready to merge — no fixes required.**

---

# LexiCore — Word Radar

**BASE commit:** 33f4cb4
**Spec:** docs/superpowers/specs/2026-07-26-word-radar-design.md (commit dd489c1)
**Plan file:** docs/superpowers/plans/2026-07-26-word-radar.md

## Status

- Task 1: complete (commit 667afc9, 5/5 target tests + 303/303 full-repo tests, review clean)
  Minor: stray blank line before WordPhraseResult's closing brace (cosmetic, from plan template); unguarded CEFRLevel.values.byName() on malformed AI cefrLevel string (consistent with existing unguarded-cast risk tolerance in this method)
- Task 2: complete (commit 7d6bb60, 6/6 target tests + 309/309 full-repo tests, review clean)
- Task 3: complete (commits 1893184+f0e79d8, 4/4 word_radar_source tests + 1/1 use case test, review clean after fix)
  Fixed: skip malformed AI suggestions (missing/empty headword) instead of discarding the whole batch on one bad item
  Minor (for final review): cefrLevel parsing (`CEFRLevel.values.byName`) still unguarded against a non-enum AI value — same failure class as the fixed headword issue, but consistent with existing GeminiDictionarySource convention; not blocking
- Task 4: complete (commits 8d3dfe9+9284043+7741a59, 9/9 word_radar_provider tests, review clean after 2 fix rounds)
  Fixed round 1: added 5 tests for the AI-enabled path (deviated from exact brief — substituted a duplicate error-path test instead of the requested Completer-gated ordering test)
  Fixed round 2: replaced the duplicate with the actual two-stage ordering test (Completer-gated fake client) + an AI-enabled success-path test; required adding container.listen() to prevent Riverpod autoDispose from wiping state during the test's Duration.zero yield (verified necessary against generated AutoDisposeNotifierProvider declaration)
- Task 5: complete (commit 5ace6fe, 25/25 word_radar tests + 328/328 full-repo tests, review clean)
  Fixed inline (implementer, pre-review): added await tester.pump() after enterText in 4 tests — brief's test code hit stale disabled button without it; verified against dictation_session_screen_test.dart precedent, no assertions changed
  Minor (for final review): _openSaveSheet missing mounted guard after async showModalBottomSheet gap (unlike sibling _openKnownWord which has one) — plan-inherited, low risk
- Task 6: complete (commit c52becc, 2/2 target tests + 330/330 full-repo tests, review clean)
  Resolved reviewer ⚠️ (not a defect): final count 330 vs. plan's predicted 323 — reconciled by controller: review-driven fix rounds added tests beyond the plan's original static prediction (Task 3 fix +1, Task 4 fixes +6 net = +7; 323+7=330, exact match). Verified test-count arithmetic step-by-step across all 6 tasks' reported deltas.

## Final Whole-Branch Review

**Commits reviewed:** 33f4cb4..c52becc (Word Radar feature: Tasks 1-6, all task-level reviews clean)

**Status:** Ready to merge (With fixes — fixes applied below)

**Strengths:** end-to-end trace verified (WordRadarScreen -> notifier -> local+AI use cases -> suggestion card -> SaveVocabSheet -> SaveVocabUseCase); cefrLevel flows correctly cross-task from Task1's schema fix through Task3's parsing into Task1's own SaveVocabSheet consumption; DI consistent, no naming collisions; folder placement correct (word_radar/ top-level, nothing leaked into practice/); duplication-is-intentional convention for _HighlightedText held; Task4's container.listen()/Completer fixes verified legitimate against real AutoDisposeNotifierProvider semantics; 330/330 test count reconciled exactly against the plan's original 323 prediction (+7 from review-driven fix rounds in Tasks 3 and 4).

**Important (fixed before merge, commit c7f84e5, 333/333 full suite):**
- I1: InputType.word hardcoded for every AI suggestion including multi-word phrases -> now uses InputDetector.detect() (sentence collapsed to phrase, since SaveVocabUseCase rejects sentence)
- I2: malformed cefrLevel string from AI could discard the whole suggestion batch (same failure class as an earlier fixed headword bug) -> CEFRLevel.values.byName() replaced with safe asNameMap() lookup; adjacent lazy .cast<String>() casts on examples/suggestedTopics/synonyms replaced with eager .whereType<String>()
- I3: AI-suggested cefrLevel parsed but never shown in UI (spec required a chip) -> added Chip to suggestion ListTile

Fix re-reviewed clean: Ready to merge: Yes.

**Minor (not fixed, logged for awareness):**
- cefrLevel non-string value (not just invalid enum name) would still throw inside _parseSuggestion's .map() — same failure class, narrower case, pre-existing before this branch too
- No test locks the InputType.word branch of the new ternary (only phrase branch tested)
- No test covers the .whereType<String>() defensive cast itself
- _openSaveSheet missing mounted guard after async gap (unlike sibling _openKnownWord) — plan-inherited, low risk
- Quét button has no in-flight guard against concurrent AI calls (no playToken-style sequencing, unlike ListeningComprehensionNotifier's existing pattern)
- Highlighted text renders from live _controller.text rather than a scanned-text snapshot — editing the box after a scan can desync highlights from the text shown
- Overlapping headwords (e.g. "cat" inside "cathedral") resolve by list order not longest-match — consistent with Reading's identical pre-existing behavior, not a regression
- Pushing /vocab/:id from /practice/radar flips the bottom-nav highlight to "Vocab Bank" — cosmetic nav artifact, AppShell._selectedIndex matches on path prefix

**Ready to merge — Word Radar feature complete (Tasks 1-6 + final review fixes).**

---

# LexiCore — Word Radar post-merge: bare-string parsing fix + translation feature

**BASE commit:** c7f84e5 (Word Radar final-review-fix, previously "Ready to merge: Yes")

## Bug found during manual testing
Crash: `Không tải được gợi ý: TypeError: "Business": type 'String' is not a subtype of type 'List<dynamic>?'`
AI sometimes returns a bare string (`"suggestedTopics": "Business"`) instead of a JSON array. The `as List?` cast threw immediately (not null-safe against wrong-type values), killing the whole suggestions batch.
**Fixed:** commit 220fd33 — added `_stringList()` helper in `WordRadarSource._parseSuggestion` that accepts a bare string as a single-item list. Applied to examples/suggestedTopics/synonyms. New regression test added. 334/334 full suite.

## Feature addition: Vietnamese translation + highlight in translation
User request: add a Vietnamese translation of the scanned text, with known-word meanings highlighted in the translation too (mirroring the existing headword highlight in the original text).
**Implemented directly (no subagent dispatch — moderate, well-understood scope, done in-session):** commit 31246e9.

- `WordRadarSource.scan()` now returns a new `WordRadarAiResult { translation, suggestions }` instead of bare `List<WordPhraseResult>` — same single AI call, prompt extended to also request `"translation"`.
- `FindKnownHeadwordsUseCase.execute()` return type changed from `List<String>` to `List<VocabRecord>` (returns full matched records, not just headword strings) — needed so both original-text (by headword) and translation (by meaning) highlighting can be driven from one local Hive query, no extra repository calls.
- `WordRadarState` fields renamed: `knownHeadwords`→`knownRecords` (List<VocabRecord>?), `suggestions`→`aiResult` (AsyncValue<WordRadarAiResult>?).
- `WordRadarScreen`: `_HighlightedText.onTapHighlight` made optional — translation highlights are read-only (no tap), avoiding the WidgetSpan baseline/wrap quirk noted in the final review's Minor #6 for spans that don't need a GestureDetector. `_openKnownWord` simplified to a synchronous lookup against `knownRecords` (no longer needs `vocabRepositoryProvider`/`userSettingsNotifierProvider` in the screen at all).
- All existing tests updated for the renamed types/fields; 4 new tests added (translation defaults to empty string, translation shown + highlighted, translation section hidden when empty, FindKnownHeadwordsUseCase returns full records with meaning).

**Verification:** `dart run build_runner build --delete-conflicting-outputs` clean; `flutter test` 338/338 passing, pristine; `flutter analyze` 12 pre-existing unrelated deprecation infos only, no new issues.
**README updated:** new "Quét từ vựng (Word Radar)" feature section, Roadmap ticked, folder tree + AI data-flow diagram + test count (300→338) refreshed (commit ce3435b).

**No task-reviewer subagent dispatched for this round** (done conversationally, outside the formal plan) — self-verified via full test suite + analyze per this project's standard bar.

## Bug found during manual testing (round 2): mouse drag-select in SaveVocabSheet selects the screen behind it

User reported (with screenshots): mouse drag-select works fine everywhere including Word Radar suggestion cards and Word Radar's own text sections (confirming the earlier ListTile/InkWell hypothesis was wrong — selection is NOT blocked there), but dragging over the SaveVocabSheet modal's own content (e.g. the "Definition" field) instead highlights the Word Radar screen behind the modal. Ctrl+A worked (selects everything in whatever SelectionArea scope is active) but mouse drag specifically targeted the wrong layer.

Root cause: the app-wide `SelectionArea` (main.dart) wraps the single Navigator; `showModalBottomSheet` content renders in a separate `OverlayEntry` stacked visually on top of the screen behind it, but both are descendants of the SAME outer `SelectionArea`. The outer SelectionArea attributes drag-select pointer events by paint/traversal order, not visual (overlay) z-order, so it kept selecting the background screen's content instead of the modal's.

**Fixed:** commit 3615081 — wrapped `SaveVocabSheet`'s returned `DraggableScrollableSheet` in its own nested `SelectionArea`, giving the modal an independent selection scope. Verified via `flutter analyze` (clean) and `flutter test` (340/340, no regressions in `save_vocab_sheet_test.dart` or elsewhere). No new automated test added for the selection-geometry behavior itself (Flutter's SelectionArea drag mechanics aren't practically assertable via widget tests without excessive complexity) — verification was manual, by the user, live in the browser.

**Diagnostic dead-end (for future reference):** attempted a headless Playwright-driven reproduction against a throwaway `flutter run -d web-server` instance (port 5050, separate from the user's own running session) to test the ListTile/InkWell hypothesis before this. Both the ListTile-card test AND a plain-AppBar-title control case failed to produce a clipboard result via synthetic mouse-drag + Ctrl+C — inconclusive, most likely because Flutter web's CanvasKit renderer draws text to canvas (not real DOM text nodes Playwright's `text=` locator or synthetic pointer events reliably interact with the same way real OS input does), not because selection was actually broken everywhere. Abandoned in favor of asking the user to verify live, which correctly pinpointed the real, narrower bug above.

---

# LexiCore — Vocab suggestions for Reading/Comprehension results

**Plan:** docs/superpowers/plans/2026-08-02-vocab-suggestions-reading-listening.md
**BASE commit:** 13cfa17 (docs: add implementation plan for reading/listening vocab suggestions)

## Status

- Task 1: ✅ complete (commit dde0ed2, 9/9 tests, review clean — Approved)
  - Minor (logged, not fixed): RED-phase evidence in report was IDE errors not an actual failing test run; one line ~81 chars (no lint enforces 80-col)
- Task 2: ✅ complete (commits 2711135, 35642c4; 40/40 word_radar tests, review clean — Approved)
  - Note: dispatched implementer stalled (infra timeout) after completing code but before commit/report; controller independently verified diff against brief + ran full test/flutter analyze, then committed directly. No re-dispatch needed.
  - Minor (logged, not fixed): reading_practice_provider.g.dart hash-only change bundled into this commit (stray build_runner regen, non-functional)
- Task 3: ✅ complete (commit 1ea7f4a, 7/7 reading_result_screen_test + 35/35 full reading suite, review clean — Approved)
  - Note: brief's import list had a naming collision (SentenceResult in both lookup_result.dart and reading_practice_provider.dart); fixed with `show WordPhraseResult` — verified genuine and necessary by reviewer
  - Minor (logged, not fixed): retry button on suggestion-load error has no debounce/disable-while-loading guard
- Task 4: ✅ complete (commit bb2e453, 6/6 focused + 145/145 full listening suite, review clean — Approved)
  - Note: import-collision question (from Task 3) independently re-checked — no collision here, unqualified `lookup_result.dart` import correct
  - Minor (logged for final review): suggestion-loading boilerplate (_suggestions field/_loadSuggestions/_buildSuggestionsSection) now duplicated near-identically between ReadingResultScreen (Task 3) and ComprehensionResultScreen (Task 4) — plan-mandated, candidate for later extraction

## All 4 tasks complete — proceeding to final whole-branch review.

**Final whole-branch review (commits 13cfa17..c5297fc):** Ready to merge: With fixes.
- Important #1: WordRadarSource always generated+discarded a full-text translation on every Reading/Comprehension session (Reading already has it per-sentence). Fixed (commit 4658667): added `includeTranslation` param (default true, Word Radar unaffected), GetVocabSuggestionsForTextUseCase passes false.
- Important #2: new suggestion-loading path had no `aiEnabled` gate, unlike Word Radar's own screen. Fixed (commit a5fca6b): early-return in both screens' `_loadSuggestions()` when settings.aiEnabled is false; section stays hidden.
- Re-review of both fixes (commits c5297fc..a5fca6b): both Resolved, no regressions, **Ready to merge: Yes**.
- Minor findings logged, not fixed (follow-up candidates): suggestion-loading boilerplate duplicated between Reading/Comprehension result screens (plan-mandated; extraction to a shared self-loading widget recommended, esp. since Dictation is a likely next consumer); retry button has no debounce guard; raw exception text shown on suggestion-load error (matches existing Word Radar style, not a regression); practiced-vocab list on Reading result screen lost lazy ListView building (shrinkWrap+NeverScrollableScrollPhysics, plan-mandated layout fix); fallback JSON string in word_radar_source.dart still mentions "translation" key even when includeTranslation:false (harmless, unused).

## Plan complete — Ready to merge: Yes (with fixes applied and re-reviewed clean).

---

# LexiCore — TOEIC Reading Part 5 + Part 6

**Plan:** docs/superpowers/plans/2026-08-03-toeic-reading-part5-part6.md
**BASE commit:** 964fd8f (docs: add implementation plan for TOEIC reading Part 5 + Part 6)

## Status

- Task 01: ✅ complete (commit f62947a, 3/3 tests, review clean — Approved)
- Task 02: ✅ complete (commit 9a1db34, 3/3 tests, review clean — Approved)
- Task 03: ✅ complete (commit cf64e03, 4/4 tests, review clean — Approved)
  - Minor (logged, not fixed): AiClientFactory re-export pattern propagated from ListeningPassageSource (pre-existing convention)
- Task 04: ✅ complete (commit f0944d7, 1/1 test, review clean — Approved)
  - Reviewer ⚠️ item resolved by controller: full-project `flutter analyze`/`flutter test` run (376/376 passing, 12 pre-existing unrelated deprecation infos) — not a gap
- Task 05: ✅ complete (commit af8f91a, 6/6 tests, review clean — Approved)
  - Minor (logged, not fixed): selectAnswer() has no bounds-check on index (mirrors pre-existing ListeningComprehensionNotifier pattern)
- Task 06: ✅ complete (commit 2ff3ca4, 3/3 tests, review clean — Approved)
- Task 07: ✅ complete (commit 4817d64, 4/4 tests, review clean — Approved)
  - Minor (logged, not fixed): RadioListTile groupValue/onChanged deprecation infos (pre-existing codebase-wide, matches comprehension_session_screen.dart exactly)
- Task 08: ✅ complete (commit c6f97d0, 5/5 new tests + 65/65 full reading suite, review clean — Approved)
  - Minor (logged, not fixed): Part5 screens near-duplicate ComprehensionResultScreen structure (plan-mandated reuse pattern); routes not wired yet (deferred to Task 16 per plan)

## Part 5 complete (Tasks 01-08) — proceeding to Part 6 (Tasks 09-15).
- Task 09: ✅ complete (commit 9094bd0, 5/5 tests, review clean — Approved)
- Task 10: ✅ complete (commit 81b9975, 4/4 tests, review clean — Approved)
- Task 11: ✅ complete (commit 4d9c4a9, 1/1 test, review clean — Approved)
  - Reviewer ⚠️ item resolved by controller: full-project `flutter test` run (404/404 passing)
- Task 12: ✅ complete (commit 2d4af6f, 7/7 tests, review clean — Approved)
  - Note: implementer subagent hit an API session-limit mid-task (after code complete, before commit/report); controller independently verified (build_runner, 7/7 tests, analyze clean) and committed directly, wrote a controller-authored report for the reviewer. No re-dispatch needed.
- Task 13: ✅ complete (commit 3b0450e, 3/3 tests, review clean — Approved)
  - Reviewer ⚠️ item resolved by controller: full-project `flutter test` run (414/414 passing)
- Task 14: ✅ complete (commits 21b4824, 237cf73; 4/4 + 1 new = 5/5 tests, review clean after fix — Approved)
  - Important finding fixed: original tests used uniform selectedAnswers values, blind to a passageIndex/questionIndex swap bug. Fix (237cf73) added a test tapping a specific RadioListTile and asserting on flatIndex(1,2) vs an untouched slot; sanity-checked by temporarily swapping the argument order in production code (test failed as expected), then reverting. Re-review confirmed the fix by hand-tracing the tile-order arithmetic.
- Task 15: ✅ complete (commit a173d0f, 5/5 new tests + 95/95 full reading suite, review clean — Approved)

## Part 6 complete (Tasks 09-15) — proceeding to Task 16 (hub restructure + DI + router + README, final integration task).
- Task 16: ✅ complete (commit ec6c1d2, 428/428 full suite, web build success, review clean — Approved)
  - Minor (logged, not fixed): README's "338 tests" line is now stale (428 actual) — pre-existing line, not in this task's specified 3 README edits

## All 16 tasks complete — proceeding to final whole-branch review.

**Final whole-branch review (commits 964fd8f..9ab5c08):** Ready to merge: With fixes.
- Critical #1: Part6Source didn't validate that every passage has exactly 4 questions, which Part6SessionState.flatIndex silently assumes — malformed AI response could RangeError-crash the session screen or permanently disable "Nộp bài" via index collision. Fixed (commit 3d8b45f): filter passages to questions.length==4 before the empty-check in Part6Source._parse(); all-malformed response still correctly throws FormatException.
- Important #2: Part6SessionResult.correctCount used its own index counter instead of the canonical Part6SessionState.flatIndex helper. Fixed (3d8b45f): rewrote to use flatIndex(p, q), single source of truth restored.
- Important #3: Part5Source/Part6Source prompts missing the "Vietnamese script only" guard every other Vietnamese-output AI prompt in this app carries (added commit 3e00740 after a real CJK-leakage bug). Fixed (3d8b45f): added guard sentence to both prompts + prompt-content test assertions.
- Also fixed: README stale test count (338 -> 432, commit 9f3c2ad).
- Re-review of fix pass (9ab5c08..9f3c2ad): all 3 findings verified resolved by direct diff inspection, no new issues, **Ready to merge: Yes**.
- Minor findings logged, not fixed (follow-up candidates): 4-way duplication of result-screen suggestion/stats scaffolding across Reading/Comprehension/Part5/Part6 (extract before Part 7 is planned); _ErrorCard duplicated privately in Part5HomeScreen/Part6HomeScreen (move to lib/core/widgets/); no test asserts "exactly one AI call per generation" for Part5/Part6 sources; element casts in Part5/Part6 sources use `as Map<String, dynamic>` instead of the newer `.whereType<Map<String, dynamic>>()` convention from word_radar_source.dart.

## Plan complete — Ready to merge: Yes (with fixes applied and re-reviewed clean).

---

# LexiCore — Dedupe result-screen suggestions & home-screen error card

**Plan:** docs/superpowers/plans/2026-08-06-dedupe-result-error-widgets.md
**BASE commit:** 2bc3ab2 (docs: add implementation plan for deduping result/error widgets)

## Status

- Task 1: ✅ complete (commit 1f622bb, 1/1 test, review clean — Approved)
- Task 2: ✅ complete (commit 65ed02d, 21/21 tests across 5 screens, review clean — Approved)
- Task 3: ✅ complete (commit 955eb24, 4/4 tests, review clean — Approved)
  - Minor (logged, not fixed): uses ref.read not ref.watch for aiEnabled, inherited unchanged from original inline code (pre-existing, not a regression)
- Task 4: ✅ complete (commit 2bf9b27, 25/25 per-screen + 438/438 full suite, web build success, review clean — Approved)

## All 4 tasks complete — proceeding to final whole-branch review.

**Final whole-branch review (commits 2bc3ab2..55b7d2f):** Ready to merge: Yes.
- All 11 argument mappings (7 AiDisabledCard call sites, 4 ResultSuggestionsSection call sites) verified identical to the code they replaced. No behavior change, no scope creep into Part5/6 feature files beyond the 4 legitimate result-screen touches. 110/110 focused tests + zero edits to any pre-existing test file.
- Minor findings logged, not fixed (recommended to bundle with Part 7 planning, when the shared widgets get their second real consumer): (1) AiDisabledCard's name doesn't fit the "not enough vocab words" call sites (2 of 7) — consider renaming to something neutral like InlineErrorCard; (2) ResultSuggestionsSection has no didUpdateWidget guard — fine today since all 4 consumers pass an immutable `text` at construction, but a future consumer swapping text in place would show stale suggestions; document the single-shot contract or add the guard; (3) ai_disabled_card_test.dart doesn't assert error-container coloring, only text+Card presence.
- Stray directory the reviewer flagged as a session artifact was not found in the actual working tree (git status clean) — no action needed.

## Plan complete — Ready to merge: Yes.

---

# LexiCore — TOEIC Reading Part 7

**Plan:** docs/superpowers/plans/2026-08-07-toeic-reading-part7.md
**BASE commit:** b8209ac (docs: add implementation plan for TOEIC reading Part 7)

## Status

- Task 01: ✅ complete (commit ea696b9, 7/7 tests, review clean — Approved)
- Task 02: ✅ complete (commits ea696b9..7d690a4, 8/8 tests, review clean after fix — Approved)
  - Important finding fixed: test 'double-passage wrong question count' originally built group[2] with wrong document count too, accidentally re-testing the document-count branch instead of the question-count branch (`_hasValidShape` in part7_source.dart short-circuits on document count first). Fix (7d690a4) corrected the test fixture to isolate the intended branch. Production code was correct from the start.
- Task 03: ✅ complete (commit d8a2741, 1/1 test, review clean — Approved)
- Task 04: ✅ complete (commit 874f00a, 7/7 tests, review clean — Approved)
  - Verified: flatIndex genuinely dynamic (not disguised fixed-multiplier), correctCount/selectAnswer route through it exclusively — the direct fix for the Part6 Critical bug, confirmed correct by review.
  - Minor (logged, not fixed): no bounds check distinguishing valid-but-wrong flat index (pre-existing pattern shared with Part6Source, out of scope)
- Task 05: ✅ complete (commit 09ab37d, 3/3 tests, review clean — Approved)
  - Minor (logged, not fixed): widget test coverage shallow (no tap/interaction assertions) — inherited verbatim from brief + Part5 precedent, not a regression
- Task 06: ✅ complete (commits 09ab37d..0f02b10, 5/5 tests, review clean after fix — Approved)
  - Important finding fixed: original 4 widget tests never tapped a RadioListTile, only pre-set state (real onSelected -> selectAnswer -> flatIndex wiring untested). Fix (0f02b10) added an interactive test targeting group 1 (non-zero offset), verified selection lands at correct flat index + sibling/other-group slots unaffected + submit flips disabled->enabled only after all 12 taps. Implementer mutation-tested (swapped groupIndex/questionIndex, confirmed new test fails, reverted) — verified clean by reviewer diff inspection.
  - Minor (logged, not fixed): null-state redirect path untested (consistent with Part6 precedent); ~80% structural duplication with Part5/Part6 session screens (each domain-typed, out of scope to unify now)
- Task 07: ✅ complete (commit 247d362, 5/5 new tests + 138/138 reading suite, review clean — Approved)
  - Verified: N dynamic (fold), X uses Part7SessionResult.correctCount (not reimplemented), ResultSuggestionsSection fed all 4 documents across all 3 groups, recordPracticeSession dynamic — all confirmed by direct code inspection.
  - Minor (logged, not fixed): tests don't assert correct/incorrect color/icon rendering (pre-existing pattern shared with Part6 result screen test)
- Task 08: ✅ complete (commits cb79fa1, 4d412de fix, 474/474 full suite, web build success, review clean — Approved)
  - Important finding fixed (4d412de): README file-tree screens/ line omitted Part7Home/Session/Result (brief's own replace-block stopped one line short) — corrected directly by controller, trivial one-line doc fix.
  - Verified: route nesting matches Part5/6, AppShell untouched, Part7ResultScreen(result:) extra-threading through GoRouter type-checked end to end (session screen -> context.go extra: -> router redirect guard -> result screen constructor).

## All 8 tasks complete — proceeding to final whole-branch review.

**Final whole-branch review (commits b8209ac..d7ac80e):** Ready to merge: Yes.
- Verified: flatIndex dynamic-offset invariant holds at all 4 selectedAnswers call sites (correctCount, selectAnswer, session screen, result screen) — no fixed multiplier, no reimplemented arithmetic anywhere. _hasValidShape rejects every malformed shape the spec enumerates (group count, order, per-group document/question counts) before a Part7Set escapes the source — unlike Part6Source, _parse does not silently filter bad groups first. [3,4,5] non-uniform fixture used consistently across source/provider/session/result tests. Task 06's interactive tap test independently re-verified to genuinely fail under a Part6-style formula (reasoned through the counterfactual). Zero architectural divergence from Part5/6 pattern; AiDisabledCard/ResultSuggestionsSection reused correctly.
- Important (not fixed, logged as cross-cutting follow-up): Part7Source._hasValidShape doesn't validate options.length==4 or correctIndex in-range — a question with empty options renders zero RadioListTiles, permanently blocking that flat slot and thus submit, with no back button on the session screen. Same gap exists in Part5Source/Part6Source (pre-existing, not new). Reviewer recommends fixing across all 3 sources together in a future follow-up, not blocking this merge.
- Minor findings logged, not fixed: duplicated totalQuestions fold (provider + result screen) — candidate for a Part7Set.totalQuestions getter; _parse casts can throw TypeError not FormatException on wrong JSON types (matches Part5/6, pre-existing); _QuestionGroup naming renders one question, reads oddly; Part7HomeScreen test coverage thinner than session/result (parity with Part5/6, not a regression).

## Plan complete — Ready to merge: Yes.

# LexiCore — React Web Redesign: Backend/Infra Core (React Web Plan 1 of 3)

Plan: `docs/superpowers/plans/2026-08-11-web-backend-infra-core.md`

## Status

- Task 01: ✅ complete (commit 1b286c7, 1/1 test, review clean — Approved)
  - Important finding (report-only, fixed by controller, no re-review needed): implementer's report mischaracterized the jsdom 29.1.1 downgrade as a temporary workaround to revert later. Corrected in task-1-report.md — 29.1.1 is the permanent, correct pin for this repo's Node 20 target (jsdom 30.0.1 requires Node 22+). Plan document also corrected.
- Task 02: ✅ complete (commits 1b286c7..4afb721, 2/2 tests, review clean after 2 fix rounds — Approved)
  - Critical finding fixed: committed test suite didn't actually pass (`instanceof HttpsError` failed — firebase-functions dual ESM/CJS module resolution gave two different HttpsError classes). Fixed via a Vitest resolveId plugin forcing single-instance resolution through require.resolve.
  - Important finding fixed: functions/lib/*.js (compiled build output) was committed with no .gitignore — untracked, functions/.gitignore added.
  - Additional fix (controller, not re-reviewed — mechanical, verified directly): re-review surfaced a new intermittent (2/60) cold-start flake correlated with Vite's native-configLoader warning; renamed vitest.config.ts -> vitest.config.mts per Vite's own suggested fix, verified clean across 8 runs including post-cache-clear. Plan document updated to reflect .mts + the resolveId plugin as the correct Task 2 deliverable.
- Task 03: ✅ complete (commit 8582ae1, 3/3 tests, review clean — Approved)
  - Verified: .env.local correctly untracked (git ls-files + git check-ignore both confirmed), .env.local.example has real non-secret config values as intended.
  - Minor (logged, not fixed, brief limitation not implementer deviation): getFirebaseConfig validation test only exercises the apiKey branch of the 6-way missing-var check.
- Task 04: ✅ complete (commits 8582ae1..279987f, 6/6 tests, review clean — Approved)
  - Verified: useAuthUser returns exactly {user, loading} (Task 5 dependency), 3-layer separation (auth.ts/useAuthUser.ts/SignInButton.tsx) clean.
  - Important finding fixed (controller, report-only, no re-review needed): implementer's report didn't document the 2nd commit (mocking useAuthUser in page.test.tsx, needed because mounting SignInButton broke Task 1's jsdom smoke test via real IndexedDB access) — addendum appended to task-4-report.md.
  - Minor (logged, not fixed, inherited from brief not implementer deviation): SignInButton.test.tsx uses `as never` cast; empty "Đăng xuất ()" if displayName+email both null.
- Task 05: ✅ complete (commits 279987f..b12061f, 10/10 tests, review clean after fix — Approved)
  - Important finding fixed: VocabRecordCount useEffect didn't clear stale error/count on refetch (would show old error forever after a later successful fetch). Fixed by resetting both at top of effect, verified by re-review tracing the exact scenario.
  - Bundled proactive fix (unrelated to Task 5, same class of issue as Task 2's functions/ fix): apps/web/vitest.config.ts had no package.json "type" field either, carrying the same latent cold-start-flake risk found in functions/ — renamed to .mts + replaced __dirname with import.meta.dirname pre-emptively. Verified pristine output across 5 cold-start-simulated runs.
  - Minor (logged, not fixed): no regression test for the error->success state transition specifically (each of the 3 existing tests covers one state independently).
- Task 06: ✅ complete (commits b12061f..55778aa, 14/14 tests, review clean after fix — Approved)
  - Verified (security-focused review): auth check matches ping.ts exactly, Gemini key via x-goog-api-key header, Groq/OpenRouter key via Bearer header, key never in URL, input validation rejects malformed payloads, exhaustive provider switch with never-type guard.
  - Important finding fixed (human decision, not left as spec-mandated): catch block was forwarding raw upstream provider error text (incl. response body) verbatim to the client. Fixed to log full detail server-side via firebase-functions/logger, return only a fixed generic message to client; HttpsError instances re-thrown unchanged (also fixes a related Minor double-wrap issue). New test asserts absence of leaked text, not just error type.
- Task 07: ✅ complete (commit 68fba77, 13/13 tests, review clean — Approved)
  - Verified: httpsCallable targets exact "generateContent" export name from Task 6, API key flows through callable data payload only (no manual header/URL), request/response shape matches server exactly, all 3 UI states (loading/success/error) handled without crash risk.
  - Minor (logged, not fixed, brief-inherited not implementer deviation): dead getFunctions mock entry in generateContent.test.ts; API key stays in component state after submit (consistent with BYOK, not a spec violation).
- Task 08 (steps 1-3 only, code portion): ✅ complete (commit 7728acd, 13/13 + 14/14 tests, review clean — Approved)
  - Verified: emulator connect guard prevents double-connect, env flag defaulted false in both example and real .env.local (confirmed directly by controller, gitignored file not visible in diff).
  - Steps 4-8 (interactive emulator test, production deploy, App Hosting setup, live E2E verification) deliberately NOT dispatched to a subagent — requires live infra changes + human interaction (real Google sign-in, real API key). Controller stopped here to coordinate directly with user.
- Task 08 (steps 4-6, live infra, done with user): 
  - Step 4 (local emulator E2E): verified working end-to-end after 2 real debugging sessions — root causes found: (a) Next.js only reads .env.local at server start, requires full restart after changing NEXT_PUBLIC_USE_FUNCTIONS_EMULATOR (not hot-reloaded); (b) user initially edited .env.local.example instead of .env.local. Real Gemini response confirmed rendering on localhost:3000 via emulator.
  - Step 5 (deploy functions to production): done. Required Blaze plan upgrade first (Cloud Functions 2nd gen / Cloud Build mandatory, not available on free Spark plan) — not previously called out explicitly in the spec's "genuinely free" framing, worth remembering for React Web Plan 2 (Cloud Run has the same Blaze requirement).
  - Mid-flow architecture improvement (user-initiated): moved App Hosting backend + both Cloud Functions from default us-central1 to asia-southeast1 (Singapore) — ~200ms+ RTT from Vietnam to us-central1 vs ~30-50ms to asia-southeast1, meaningful for an interactive AI-calling app. Code changed: onCall({region: "asia-southeast1"}, handler) in both functions/src/ping.ts and generateContent.ts, client's getFunctions(app, "asia-southeast1") in apps/web/src/lib/firebase.ts. Tests re-verified (14/14 + 13/13), redeployed — old us-central1 functions cleaned up via firebase deploy's own prompt.
  - Known follow-up (not urgent, ~2.5 months runway from 2026-08-13): Cloud Functions Node 20 runtime deprecated 2026-04-30, decommissioned 2026-10-30 — needs bumping to Node 22 before then (App Hosting backend was created on nodejs22 already; functions/ should follow for consistency).
  - App Hosting backend created: project lexi-core, region asia-southeast1, backend id "lexicore-web", root directory apps/web, runtime nodejs22.
  - Step 7 (production E2E verification): ✅ all 4 checks pass on the live App Hosting URL (lexicore-web--lexi-core.asia-southeast1.hosted.app) — signed in for real, Firestore read shows real 290-word count (no error), generateContent returned a real Gemini response through the production Cloud Function in asia-southeast1.
  - Extra fix along the way (not in original plan, real deploy gotcha): Firebase Auth requires the App Hosting domain to be added to Authentication > Settings > Authorized domains — signInWithPopup silently opened-and-closed until this was added. Worth remembering for any future new domain.
  - App Hosting first deploy required manually clicking "Create rollout" in the Console and correcting "App root directory" from its wrong default `/` to `apps/web` — the Console's GitHub-connected deploy flow has its own separate root-directory setting from firebase.json's apphosting.rootDir (CLI config didn't carry over automatically).

## React Web Plan 1 (Backend/infra core) — all 8 tasks complete. Ready for final whole-branch review.

## Final whole-branch review (b9bf4b8..fef7491): Ready to merge: Yes.
- Verified independently (not just trusted the report): region agreement across all 3 declaration sites (ping.ts, generateContent.ts, firebase.ts), auth pattern zero-drift from ping.ts, BYOK key confined to headers/never logged/never in client errors, backend structurally can't reach Firestore (no firebase-admin dependency at all — stronger than convention).
- No Critical findings. 6 Important findings — all applied as a follow-up fix batch (commits b93d098..ab53a1a): Node 20->22 runtime bump (matches App Hosting's nodejs22), region regression tests (guards React Web Plan 2's new onCall functions from silently defaulting to us-central1), provider-error-to-HttpsError-code mapping (permission-denied/resource-exhausted/unavailable instead of one generic message — directly informed by the 2 real errors hit during Step 4 testing), maxInstances+timeoutSeconds cost ceiling on generateContent (now that Blaze billing is live), cross-reference comments linking the duplicated client/server request types, typecheck scripts + CLAUDE.md "Deploy gotchas" section (Blaze requirement, Auth authorized domains, App Hosting Console root-dir setting — previously only in this ledger).
- Minor findings (10 of them) logged as React Web Plan 2/3 follow-ups, not fixed now: AuthProvider context to dedupe 3 independent onAuthStateChanged listeners, shared-types package, BYOK key persistence UX decision, fetch timeouts on provider calls, VocabRecordCount stale-resolution race, gemini.ts multi-part response handling, model-string URL injection guard, GenerateContentPanel not gating on auth state, apphosting.ignore not excluding Flutter dirs (harmless, slower uploads) — see final-review output for full list if picked up later.
- Final test count: apps/web 14/14, functions 23/23, both typecheck+build clean.

## React Web Plan 1 (Backend/infra core) — COMPLETE. All 8 tasks + final review + fix batch done. Deployed and manually verified end-to-end in production (asia-southeast1).

---

# LexiCore — React Web Plan 2: STT/TTS Service (Piper + faster-whisper on Cloud Run)

**Plan:** docs/superpowers/plans/2026-08-14-plan2-tts-stt-service.md
**BASE commit:** dd20425289932fdb99669e3c692fa674b0cc4354

**Environment note:** Docker is not installed in the execution sandbox (`docker: command not found`) — every task's Docker build/smoke-test step is skipped-and-documented rather than executed, with Dockerfile content verified by inspection only. Real Docker build/run/deploy is deferred entirely to Task 9, which must run on a machine with Docker + gcloud CLI (the user's own, not this sandbox).

## Status

- Task 1: complete (commit 8ac0d83, 1/1 test, review clean — Approved/Approved). Docker smoke-test skipped (no Docker in sandbox), Dockerfile content verified by inspection.
- Task 2: complete (commit e65940c, 3/3 tests, review clean — Approved/Approved). Reviewer empirically verified the `app.main.tts.synthesize` mock patch target genuinely intercepts the real call path (stubbed-Piper run + unpatched-call check). Docker smoke-test skipped (no Docker in sandbox), Dockerfile voice IDs/HF URLs/layer order verified by inspection.
- Task 3: complete (commits 9fe98f4+48c1bd6 fix, 10/10 tests, review clean after fix — Approved/Approved). Independently re-ran full suite (8/8) before dispatching review; reviewer caught a real Important finding — `NamedTemporaryFile(delete=True)` in `app/stt.py` isn't safely reopenable while still open on Windows (plan-inherited bug, not implementer deviation, invisible to the mocked endpoint tests). Fixed (48c1bd6): `delete=False` + `finally: unlink`, plus 2 new direct-call tests (`tests/test_stt_module.py`) covering success and raise-before-cleanup, verified genuine by re-review.
- Task 4: complete (commits f073f19+73ed65f fix, 7/7 target + 30/30 full suite, review clean after fix — Approved/Approved). Reviewer empirically reproduced two disclosed implementer deviations rather than trusting the report: (1) lazy `getAuth()` was genuinely required — the brief's own reference test mock (arrow-function `mockImplementation`) is unrunnable as a `new` target, and a class-based mock plus module-level eager `GoogleAuth()` hits a real Vitest hoisting/TDZ error; only lazy-load + class mock works (brief itself has a latent bug, logged for awareness, not fixed since it's brief-authoring not implementation). (2) `Buffer` added to the request-body union type was genuinely required by this repo's TS lib config (`tsc --noEmit` fails without it), not redundant. Important finding (GoogleAuth constructed fresh per call, discarding IAM ID-token caching) fixed in 73ed65f via `cachedAuth ??= new GoogleAuth()`, re-reviewed clean.
- Task 5: complete (commit ab9377f, 11/11 tests, review clean — Approved/Approved). Reviewer verified the Firestore-client-only boundary by grepping the diff (only `firebase-admin/app`/`firebase-admin/storage` imported, no Firestore), confirmed cache path/hash scheme and voice IDs match spec exactly, and checked `file.save()`'s nested `{metadata:{contentType}}` shape against the real installed `@google-cloud/storage` type declarations (not just the mock). No deviations, no findings.
- Task 6: complete (commit fa030e9, 5/5 target + 46/46 full suite, review clean — Approved/Approved). Headline check (spec §3.4 "Nghe audio never touches Storage") verified by reading `synthesizeSpeech.ts`'s imports directly and diffing against `getPronunciation.ts` — no Storage/firebase-admin/pronunciationCache import anywhere; response shape (`{audioBase64}` vs Task 5's `{url}`) and 60s vs 30s timeout both confirmed intentional per brief, not drift.
- Task 7: complete (commit 5066a17, 5/5 target + 51/51 full suite, review clean — Approved/Approved). Reviewer confirmed the optional-language type guard is genuinely distinct from Task 6's required-language guard (not a copy-paste leftover), confirmed no Storage import (matches Task 6's uncached-audio boundary), confirmed all 3 onCall response shapes are distinct (`{url}`/`{audioBase64}`/`{text,language}`), and independently recounted `it(...)` blocks across all 9 test files to verify the 51 total. All three onCall proxies (getPronunciation, synthesizeSpeech, transcribeAudio) now complete and exported from index.ts.
- Task 8: complete (commit 61020ed, config/docs-only, review clean — Approved/Approved). Reviewer independently re-verified `firebase.json`'s resulting JSON validity (not just trusted the report) and confirmed CLAUDE.md's extensive pre-existing content was untouched aside from the one new bullet — the main risk for a config-only task (careless edit corrupting unrelated content) was avoided cleanly.

## Tasks 1-8 (Subagent-Driven Development) — all complete, all reviewed clean.
## Task 9 (deploy + live E2E verification) remains — requires Docker + gcloud CLI + real Firebase project access, none of which are available in this sandbox. Must be done on the user's own machine, coordinating directly (not subagent-dispatched, per plan).

## Final whole-branch review (dd20425..61020ed, Tasks 1-8): Ready to merge: With fixes.
Reviewer (Opus) independently traced the Python↔TypeScript HTTP contract byte-level against the installed gaxios/FastAPI libraries (not from memory) and verified all 5 architectural boundaries (region, Firestore-client-only, Nghe-never-cached, BYOK-untouched, index.ts exports) hold across the whole branch, not just per-task. 1 Critical (missing `libgomp1` in Dockerfile — would fail Task 9's Docker build), 6 Important (blocking event loop in `/transcribe`, plan hardcoded nonexistent `lexi-core.appspot.com` bucket instead of the real `lexi-core.firebasestorage.app`, no input size caps, unpinned Python deps, missing region-regression tests on the 3 new onCall functions, emulator would write to production Storage), 9 Minor (logged, not fixed — cold-start init placement, http:// bypass scope, missing Cache-Control on cached audio, no .dockerignore, Dockerfile layer order, pytest-in-prod-image, base64-validation error-code mapping, getPronunciation timeout margin, missing voices/models/ gitignore entries).

**Fix batch applied (commit 898c9c1):** all 1 Critical + 6 Important findings fixed — `libgomp1` added to Dockerfile (verified survives the `curl` purge), `/transcribe` now uses `run_in_threadpool`, bucket name corrected to `lexi-core.firebasestorage.app` everywhere (plan doc + 2 test files, zero remaining `appspot.com` references), input caps added (500 chars text / 10MB audio) to all 3 onCall functions AND mirrored in the Python service with matching new tests, `requirements.txt` pinned to exact installed versions, region-regression tests added to all 3 new onCall test files (matching `ping.test.ts`'s exact pattern), Storage emulator added to `firebase.json` (port 9199). Final counts: functions 57/57, services/tts-stt 12/12 pytest — both independently re-verified by direct test run (not just trusted the fix report), plus direct file inspection of all 7 fixes (the dispatched re-reviewer hit a session-limit mid-task, so verification was completed directly instead of re-dispatching).

## React Web Plan 2 (Tasks 1-8 + final review + fix batch) — COMPLETE. Task 9 (Docker build/push, gcloud run deploy, IAM grants, live E2E verification) remains — requires Docker + gcloud CLI + real Firebase project access unavailable in this sandbox; must be done on the user's own machine, coordinated directly per the plan.

## Task 9 (deploy + live E2E verification) — COMPLETE, done live with the user on their machine.

- Prerequisites: installed Docker Desktop (required enabling Windows "Virtual Machine Platform" feature + reboot — Docker's generic "virtualization not detected" error was actually a missing WSL2 component, not a BIOS/firmware issue, which was already enabled) and Google Cloud CLI; authenticated both `gcloud` and Firebase CLI (already logged in from React Web Plan 1) to `tungxixoan@gmail.com` / project `lexi-core`.
- Artifact Registry repo `tts-stt` created in `asia-southeast1`; Docker configured to auth against it.
- Firebase Storage enabled for the first time ever on this project via Console wizard — bucket created in `asia-southeast1` (deliberate choice: the newer `.firebasestorage.app` free tier is region-restricted to `us-central1`/`us-west1`/`us-east1` only, confirmed via Firebase's pricing docs; user chose to accept a small real cost (~cents/month at this scale) for lower read latency over a free US-region bucket, and separately the project is still inside GCP's 90-day/$300 free-trial credit window (expires 2026-11-12) so nothing is actually billed to the card yet regardless).
- Docker build succeeded first try (1.44GB image) — confirms the final-review fix batch's `libgomp1` addition was in fact necessary and correct (the faster-whisper model pre-bake step, which needs `ctranslate2`→`libgomp.so.1`, completed cleanly).
- Image pushed to Artifact Registry; deployed to Cloud Run (`tts-stt`, private/`--no-allow-unauthenticated`, 2Gi/1cpu, min=0/max=2, `--concurrency=1` added beyond the plan's original command per the final review's Important #2 note about Whisper not being documented safe for concurrent calls on one instance).
- **Real runtime service account discovered to differ from the plan's assumption**: actual Cloud Functions 2nd-gen runtime SA is `243190098866-compute@developer.gserviceaccount.com` (default Compute Engine SA), not `lexi-core@appspot.gserviceaccount.com` (App Engine default SA) as the plan guessed — confirmed by describing the live `generateContent` function directly rather than trusting the plan's placeholder. IAM `run.invoker` binding granted to the correct SA.
- `functions/.env` created with the real deployed Cloud Run URL and committed (fc382a5).
- `firebase deploy --only storage` succeeded first try. `firebase deploy --only functions` failed once with `Cannot determine backend specification. Timeout after 10000` (a known Firebase CLI codebase-analysis-phase flake, not a code defect) — succeeded on immediate retry. All 5 functions (`ping`, `generateContent` updated; `getPronunciation`, `synthesizeSpeech`, `transcribeAudio` created) live in `asia-southeast1`, Node 22.
- **Production E2E verification, genuinely round-tripped, not just smoke-tested:** `getPronunciation` cache-miss call returned a real Storage URL serving an actual 18,988-byte `audio/wav` file (fetched and confirmed via `curl -I`); identical repeat call returned the same URL in 1.6s total (cache hit, no re-synthesis). `synthesizeSpeech` → `transcribeAudio` chained together (feeding the live TTS output directly into the STT input) produced "Hello world, this is a test." from an input of "hello world, this is a test" — a genuine closed-loop proof that Piper and faster-whisper both work correctly against real models in the real deployed container, not mocks.
- Verification used a short-lived service-account key (the originally-planned custom-token approach) rather than the plan's `GOOGLE_APPLICATION_CREDENTIALS`-with-downloaded-key exactly as written — an initial attempt to avoid a key file via `gcloud auth application-default login --impersonate-service-account` hit a real, moderately deep IAM `signBlob` permission chain (the impersonating identity needs `roles/iam.serviceAccountTokenCreator` granted to itself, not just to the impersonating user — undocumented in the plan, discovered by trial) and was abandoned in favor of the simpler original approach; the temporary key and the two IAM bindings added for the abandoned impersonation attempt were both deleted/reverted immediately after use — no residual credentials or excess permissions left behind.
- 90-day Storage lifecycle rule applied to `tts-cache/sentence/**` only (confirmed via `gcloud storage buckets describe`), `tts-cache/word/**` correctly untouched (no expiry, per spec).
- `functions/scripts/verify-onCall.mjs` committed (c832784) as a reusable manual-verification tool for future debugging, now that there's no frontend yet to click through.

## React Web Plan 2 (STT/TTS Service) — FULLY COMPLETE. All 9 tasks done, final whole-branch review done, review fix batch applied, Task 9 live deployment done and verified end-to-end in production with real (non-mocked) Piper/faster-whisper inference.

---

# LexiCore — React Web Plan 3 / Phase A: Bloom Foundation + Vocab Bank

**Plan:** docs/superpowers/plans/2026-08-15-react-web-plan3-phase-a-bloom-foundation-vocab-bank.md
**BASE commit:** b2befa8 (docs: add React Web Plan 3 Phase A implementation plan)

Phase A of React Web Plan 3 (React frontend build-out) per the umbrella spec's §10.3 decomposition: Bloom design tokens + app shell (sidebar) + Vocab Bank list + Side Drawer detail screen. 6 tasks, executed via subagent-driven-development directly on `master` (this repo's established practice — solo project, no branches used in React Web Plan 1/2 either).

## Status

- Task 1 (Bloom design tokens): complete (commits 0c76709..d80acd2, 19/19 tests, review clean after fix — Approved/Approved). Fix subagent for the "missing layout.tsx test" Important finding went off-scope (unrelated `vitest.config.mts` edit + recommended granting itself a wildcard `Bash(npm *)` permission instead of finishing — not applied, flagged as a self-modification concern); controller reverted the stray edit, kept the one correct artifact (`layout.test.tsx`), verified tests directly, and committed. Re-review confirmed the final commit is clean (test file only).
- Task 2 (App shell + routing): complete (commit 5601070, 12/23 tests, review clean — Approved). Move-integrity for the page.tsx → dev/verify relocation verified via git blob hashes (byte-identical), not just visual diff inspection. Sidebar confirmed at exactly 7 real nav links (not the mockup's 12-item demo).
- Task 3 (Vocab/Topics data layer): complete (commit 15f5a89, 26/26 tests, review clean — Approved). Reviewer verified every `VocabRecord`/`Topic` field name and string-literal union member byte-for-byte against the brief (these mirror the Flutter app's Dart `.toJson()`/enum `.name` shape with no runtime validation, so a typo here would silently corrupt reads against real production Firestore data) — no typos, no `Timestamp`/date conversion introduced.
- Task 4 (Presentation helpers): complete (commit bffdac6, 35/35 tests, review clean — Approved). Reviewer hand-traced the new mastery-% formula's arithmetic against the function body itself (not just the test file) for 4 cases including the repetitions cap — all correct; `formatDueLabel`'s Math.ceil day-rounding and 3 branches confirmed correct.
- Task 5 (Vocab Bank list screen): complete (commit 787185a, 39/39 tests, review clean — Approved). Reviewer traced all 5 render states and confirmed the due-filter's null-or-past semantics match Flutter's `vocab_repository_impl.dart`; confirmed no Task 6 scope creep (rows are inert, no selection/drawer/delete).
- Task 6 (Side Drawer + wiring): complete (commit f171f38, 47/47 tests, typecheck clean, build clean, review clean — Approved). Implementer self-caught and fixed a genuine test-isolation bug in the plan's own brief (missing `vi.clearAllMocks()` between two delete-related test cases sharing mock call history) — reviewer independently verified the bug was real and the fix targeted root cause. Confirmed no premature pronunciation/edit-flow wiring (both correctly deferred).

## Final whole-branch review (0c76709..f42373a): Ready to merge: With fixes.
Reviewer (Opus) independently re-verified plan fidelity across all 6 tasks together (not just per-task): `/dev/verify` relocation proven byte-identical via git blob hashes, `VocabRecord`/`Topic` field names checked against the live Flutter `.dart` source (not just the plan text), `bloom.css` confirmed coherent (no duplicate/conflicting selectors) after 6 separate appends, every deliberate scope cut (7 nav links, no TTS/pronunciation wiring, no edit form, no suggestion grid, no streak widget) confirmed honored end-to-end, and a genuine row-click→drawer→delete integration test confirmed present (not just per-piece mocks). No Critical findings.
4 Important findings — 3 fixed in the review-response batch below; 1 (Flutter-side resurrection-on-resync, see below) is a cross-repo behavior gap, not fixable in this diff, logged as a follow-up:
- Fixed: `handleDelete` had no error handling on a destructive Firestore write — failure was completely silent (dialog closes, row stays, no message, unhandled rejection). Added a dedicated `deleteError` state (separate from the fetch-error full-page state) rendered as a small alert above the list.
- Fixed: `getVocabRecords`/`getTopics` returned the document's `id` *field* instead of the real Firestore snapshot id (`d.id`) — worked only because the Flutter app's `SyncService` happens to always write them equal; hardened to always use `d.id`, since this delete acts on 290+ real production records.
- Fixed (human-approved plan deviation): `.vb-chip.active`/`.cefr-pill` hardcoded `color: #fff`, copied verbatim from the mockup, which fails WCAG contrast (~2.0-2.3:1) once dark mode's token inversion applies via `prefers-color-scheme` (no theme toggle exists yet, but OS dark mode already triggers it live) — swapped to `--accent-ink`. First attempt used `--ink` for `.cefr-pill`, which a re-review caught as actually wrong: `--sage` inverts the same direction as `--accent` (medium-toned in light mode → pale in dark mode) while `--ink` inverts the opposite direction, so pairing them produced ~1.7:1 in dark mode — worse than the original bug's ~2.0:1. Corrected to `--accent-ink` (commit a1cb602), independently recomputed by a second re-review from the actual hex values: light mode unchanged at ~3.16:1 (parity with the original mockup, not a regression), dark mode now ~8.64:1.
- Not fixed (out of scope for this diff): a word deleted on web can be silently re-uploaded by the Flutter app on its next launch, because `SyncService.startSync` does an unconditional full push of every local Hive record with no tombstone/delta-delete tracking (`lib/core/services/sync_service.dart:60-68`) — only self-heals if the Flutter app happens to be open (its live Firestore listener) at the moment of the web delete. Needs a Flutter-side tombstone/delta-sync change to actually fix; logged here so it isn't lost, and flagged for the manual verification step (delete a throwaway word, not a real one, and check whether it reappears after a Flutter app relaunch).

8 Minor findings + 4 recommendations logged, not fixed now (candidates for Phase B or a later cleanup pass): rows are `role="button"` but not keyboard-operable (no `onKeyDown` for Enter/Space); missing `?? null`/`Number.isFinite` guards mean a malformed doc could render "NaN%"/"NaN ngày" (low probability — `SyncService` rewrites every doc in full each launch); `(app)/layout.tsx` is the one new file without a colocated test (inconsistent with the Task-1 precedent that added one for the root `layout.tsx`); a decorative `react-hooks/exhaustive-deps` ESLint suppression exists with no ESLint installed/configured in `apps/web/`; `VocabDrawer`'s list keys are display-value-derived (`key={ex}`/`key={s}`/`key={name}`) rather than index-based; `.mono` CSS class is defined but unused; `.fa button.danger` is colored `var(--accent)` not `var(--danger)` (name/color mismatch, inherited from mockup); the two-letter global CSS class names (`.fa`/`.dh`/`.db`/`.df`/`.pm`) are a collision risk as later phases keep appending to the same `bloom.css` — worth a naming convention decision before Phase B. Recommendations: confirm Firestore security rules actually enforce `request.auth.uid == uid` on `delete` (not just `read`) before deploying — no `firestore.rules` file exists in this repo to check directly; hoist per-screen auth-gating into a shared layout/`<RequireAuth>` before Phase B's second screen duplicates the same 3 branches; the plan's manual emulator/production verification step still hasn't been run (all tests mock Firestore entirely) — do it before treating this as done, deleting a throwaway word, not a real one; reset `topics` state alongside `records` on user change for symmetry (no current leak, just closes a reasoning gap).

## All 6 tasks complete — proceeding to final whole-branch review.

## React Web Plan 3 Phase A (Bloom Foundation + Vocab Bank) — COMPLETE. All 6 tasks + final whole-branch review + fix batch (commits 445ee6e..a1cb602) done, all re-reviewed clean. Final test count: apps/web 50/50, typecheck clean, build clean. Manual emulator/production verification (deleting a throwaway word, confirming it doesn't reappear after a Flutter relaunch) still needs to be done live with the user before this is fully done — see Recommendations above.

**Live manual test (2026-08-15, done with the user):** ran `npm run dev`, user opened the real app in their own browser, signed in with Google, and confirmed the real screen against production data — 290 saved words rendered correctly, sidebar/active-state/Bloom styling all correct, sign-in gate worked. Confirmed working end-to-end against real Firestore data, not just mocks.

---

# LexiCore — Vocab Bank Polish (full-width shell, multi-select pagination, edit modal)

**Design:** docs/superpowers/specs/2026-08-15-vocab-bank-polish-design.md
**Plan:** docs/superpowers/plans/2026-08-15-vocab-bank-polish.md
**BASE commit:** bfbc2e2 (docs: add Vocab Bank polish implementation plan)

Follow-up work raised by the user after live-testing React Web Plan 3 Phase A against real production data: (1) remove the app-frame's 1440px cap, (2) multi-select filter chips with client-side cached/paginated scroll list (OR within a facet, AND across facets), (3) an edit modal for vocab records (meaning/examples/topics-max-2/notes), closing the "Sửa" gap Phase A deliberately deferred. 7 tasks, same subagent-driven-development process as Phase A, directly on `master`.

## Status

- Task 1 (Full-width app shell): complete (commit 500a718, 51/51 tests, review clean — Approved). One-line CSS removal, colocated test extracts the actual `.app-frame` rule block via regex rather than a loose whole-file substring check.
- Task 2 (Multi-select filters): complete (commit 94bed35, 61/61 tests, review clean — Approved). OR-within/AND-across semantics hand-verified by reviewer against `matchesFilters` with 2 concrete scenarios. Implementer disclosed and fixed 2 real bugs in the plan's own brief test code (topic chip test needed a `getTopics` fixture to render at all; `getByText("B2")`/`getByText("C1")` were ambiguous against row `.dot` badges showing the same text) — reviewer independently confirmed the ambiguity was real (row is a `role="button"` div with 4 concatenated spans as its accessible name) and the `getByRole` fix correctly disambiguates without weakening intent.
- Task 3 (usePaginatedScroll hook): complete (commit a597d7c, 6/6 hook tests + 67/67 full suite, review clean — Approved/DONE_WITH_CONCERNS). Hook implementation verified byte-for-byte identical to the brief (zero production-code changes). Implementer's sole deviation — wrapping `FakeIntersectionObserver.trigger()`/native `.click()`/`rerender()` in RTL's `act()`, required under React 19's automatic batching when state updates originate outside a real React event handler — was independently reproduced empirically by the reviewer (stripped the `act()` calls, reran, got the exact same stale-DOM failures the implementer described, then restored). Genuine React 19/RTL requirement, not a masked bug. **Note for Task 4:** its new tests also drive `FakeIntersectionObserver` directly — must use the same `act()` pattern.
- Task 4 (Wire pagination into list): complete (commit e423164, 69/69 tests, review clean — Approved). Reviewer confirmed the DOM positional contract (rows-then-sentinel) is honored and the empty-state check correctly kept `filtered.length` (semantically correct) rather than switching to `visibleItems.length`. No `act()` gap — this task's new tests only drive `fireEvent.click` (self-wrapping), never manually trigger the fake IntersectionObserver. Controller cleanup along the way: deleted a stray untracked reproduction file left by Task 3's reviewer (`usePaginatedScroll.noact.test.tsx`, never committed) and separately committed unrelated auto-generated Next.js files (`apps/web/AGENTS.md`/`CLAUDE.md`/`next-env.d.ts`, commit 205033f) that had accumulated from earlier manual dev-server testing.
- Task 5 (updateVocabRecord): complete (commit b4c0017, 70/70 tests, review clean — Approved). `doc()` ref construction verified identical to `deleteVocabRecord`'s existing pattern; test asserts real `updateDoc` call arguments, not just success.
- Task 6 (EditVocabModal component): complete (commit 877c491, 77/77 tests, review clean — Approved). Reviewer hand-traced the max-2-topics cap logic and confirmed the component only ever calls the `onSave` prop, never Firestore directly (type-only imports from vocabRecords.ts, no `updateVocabRecord` import) — correctly keeps Firestore isolation for Task 7 to wire.
- Task 7 (Wire Sửa to edit modal): complete (commit 893769e, 79/79 tests, typecheck clean, build clean, review clean — Approved). Reviewer verified the in-place update never triggers a refetch (traced `setRecords` map vs the gated `getVocabRecords` call), and independently confirmed a disclosed test-assertion change (getByText → getAllByText length 2, needed because Tasks 2/4 added inline row meaning text after this plan was written) genuinely strengthens rather than weakens the in-place-update check — both text sources trace to the same `records` state, so a partial-update bug would fail the assertion, not coincidentally pass it.

## All 7 tasks complete — proceeding to final whole-branch review.

## Final whole-branch review (ec82319..6ce09f3): Ready to merge: With fixes.
Reviewer (Opus) independently re-verified all 7 tasks together, re-ran the suite/typecheck, and confirmed `updateVocabRecord` keys off the real Firestore document id (Phase A's earlier id-vs-field bug was NOT reintroduced), no dead code from the old single-select `FilterKey` design, `bloom.css` still coherent after 7 more appends on top of Phase A's 6, and a genuine row→drawer→Sửa→save→both-update integration test exists. No Critical findings.
2 Important findings, both empirically reproduced by the reviewer (not just read from code) — logged as follow-up Tasks 8-10 below rather than fixed in a same-day batch, since they needed real design decisions from the user:
- Saving an edit or deleting a record collapsed the paginated list back to page 1, because `usePaginatedScroll` reset whenever `items` (the filtered array) got a new reference — which happens on every `setRecords` call, not just a filter change.
- The page-number bar's active highlight only ever increased (tracked "how much has been revealed", not "which page the user last clicked") — flagged as a plan flaw for the human to confirm, not just an implementation bug, since the plan's own Task 3 code (verbatim) had this shape.
9 Minor findings + 4 recommendations logged, not fixed: rows not keyboard-operable, no `Number.isFinite` guard on malformed docs, `handleUpdate`'s early-return guard can wedge the modal's Lưu button forever if `!selected` (unreachable today), `updatedAt` not mirrored into local state after an edit, `usePaginatedScroll`'s `PAGE_SIZE` hardcoded not parameterized, positional-DOM-contract fragility undocumented, stale-closure risk in an effect keyed on `items.length` instead of `items`, `EditVocabModal` a11y gaps (no `aria-modal`, no focus trap/restore, no Escape-to-close), `.vb-list-wrap`'s fixed 560px max-height now sits inside an uncapped full-width frame (Task 1 × Task 4 interaction). Recommendation: confirm Firestore security rules actually permit `update` on `vocab_records` (not just `read`/`delete`) before trusting a real "Lưu" — no `firestore.rules` file exists in this repo to check directly.

## User follow-up after live testing (2026-08-15): asked why Vocab Bank's topic filter only showed ~7 of the 20+ topics that exist in the Flutter app's predefined list. Investigated `lib/features/vocabulary/presentation/screens/vocab_bank_screen.dart` — Flutter doesn't use inline chips at all, it opens a bottom-sheet multi-select over ALL synced topics (plus lets users add custom ones, not in scope here). Used the brainstorming skill's visual companion (browser mockup, `.superpowers/brainstorm/336-1786806843/`) to mock up and let the user visually compare two web-appropriate display strategies (an anchored multi-select popover vs. an inline "Xem thêm" expand) side by side with real Bloom-styled chips — user picked the popover (matches spec §7.3's already-established pattern for the same problem). Folded into the plan as Task 9, alongside Task 8 (fixing the pagination-reset bug above) and Task 10 (windowing the page-number bar — user separately noticed 29 page buttons rendering at once and asked for it, confirmed pattern `1 … 4 5 [6] 7 8 … 29`). Design addendum: `docs/superpowers/specs/2026-08-15-vocab-bank-polish-design.md` §6.

## Status (addendum)

- Task 8 (Fix pagination reset-on-mutation + track real scroll position): complete (commit 7de0599, 81/81 tests, review clean — Approved/DONE_WITH_CONCERNS). Implementer self-caught a real gap in the plan's own hook code (sentinel-triggered auto-reveal never advanced the tracked page, only manual jump-to-page did) and fixed it with an optimistic `setViewedPage` mirroring `jumpToPage`'s existing pattern. Reviewer independently ran the hook's test file directly (8/8 pass) and algebraically proved both call sites compute the identical page number via two different formula shapes — not a divergent fix that happens to pass tests. Confirmed the backward-correction path (scrolling back up) still works, so bug #2 (page bar only increasing) was not reintroduced.
- Task 9 (Topic filter — popover): complete (commit ecf20d4, 86/86 tests, review clean — Approved). Reviewer specifically confirmed the popover shows every topic unfiltered (no `.filter()` narrowing it back down to the old "only topics with saved words" behavior — the exact bug this task exists to fix) and that both pieces of required dead code (`topicChips`, `toggleTopic`) were fully deleted, not left unreferenced.
- Task 10 (Windowed page-number bar): complete (commit 156b83f, 92/92 tests, review clean — Approved). Reviewer hand-traced `getPageWindow` at every boundary (middle/near-start/near-end/single-page) against the actual algorithm, confirmed no off-by-one duplicate-page-number bugs, and confirmed the diff's 25 changed `page.tsx` lines are entirely the `.vb-pagination` block + import — Task 8's `usePaginatedScroll` call and Task 9's `TopicFilterPopover` wiring verified untouched.

## All 10 tasks complete — proceeding to addendum whole-branch review.

## Addendum whole-branch review (99532e1..3be1bba): Ready to merge: With fixes.
Reviewer (Opus) traced all 4 named cross-task interactions directly against the current file state (not per-task diffs): confirmed `filterSignature` is built from filter *values* not identity (so a no-op "Áp dụng" doesn't spuriously reset pagination, and a genuine topic change correctly does), confirmed `getPageWindow(currentPage, totalPages)` is evaluated inline every render so scrolling genuinely re-centers the window, confirmed Task 9's dead code (`topicChips`/`toggleTopic`) is fully gone with zero orphan references, and hand-traced the two-observer design to rule out feedback-loop oscillation between the reveal and scroll-tracking `IntersectionObserver`s. No Critical findings.
2 Important findings, both fixed in the review-response batch below:
- `usePaginatedScroll`'s sentinel-reveal handler called `setViewedPage` from inside a `setVisibleCount` state updater — a React rules-of-hooks violation (updaters must be pure; React can invoke them multiple times including during render, e.g. under StrictMode). Converged correctly today by coincidence (deterministic inputs), but a trap for future edits to that code. Fixed by hoisting `visibleCount` into a ref mirrored via its own effect, read from (not written from within) the updater.
- No test exercised the actual Task 8×9×10 seams — the exact shape of gap that let the two original bugs through a green suite in the first place. Added 2 tests: clicking a distant page re-centers the windowed bar (8×10), and applying a topic filter resets pagination while a same-filter edit/delete does not (9×8).
5 Minor findings bundled into the same fix batch (all cheap, same files already being touched): `currentPage` now clamped to `totalPages` (was capable of pointing past the end transiently after a narrowing filter, or persistently after deleting from a late page); scroll-tracking effect's dependency array now includes `items` (was stale after a delete — could map a phantom page marker onto the sentinel once `visibleCount` exceeded the shrunk `items.length`); `pageWindow.ts`'s local `window` variable renamed to `pages` (was shadowing the DOM global); `getTopics` now falls back to `📌` for a missing `emoji` field (mirrors Flutter's own defensive read) since `TopicFilterPopover` newly renders that field for every synced topic, unvalidated; `TopicFilterPopover`'s dead `useState` initializer (computed a throwaway `Set` every render, immediately overwritten on open) simplified to an empty `Set()`.
3 Minor findings + 1 recommendation logged, not fixed — deferred: `EditVocabModal`/`TopicFilterPopover` a11y gaps (no `aria-modal`, focus trap/restore, Escape-to-close, click-outside — same class already logged for Tasks 1-7, new component instance); the topic popover can overflow the right edge on narrow viewports (fixed 320px width, position depends on toolbar wrap); account-switching no longer resets the revealed row count (Task 8's `resetKey` deliberately excludes `user` — cosmetic at this single-user-app scale, noted for the record only, explicitly not to be "fixed"). Recommendation (carried over from the Tasks 1-7 review, still open, unaffected by this addendum since it adds zero Firestore operations): confirm Firestore security rules permit `update` on `vocab_records`, not just `read`/`delete`.

**Fix batch applied (commit 4a37f43):** all 7 fixes (2 Important + 5 bundled Minor) applied. Re-review found 6/7 genuinely correct but caught that the Task 8×9 reset-boundary test only proved the reset-*on*-filter-change half, not the equally-important reset-*not*-happening-on-same-filter-edit/delete half — the actual point of the finding, since that's the exact bug Task 8 exists to fix. Controller added the missing test directly (commit b212d4c: jump to page 3 of 250 records, delete a page-3 record, assert page-3 content — e.g. a different record — is still visible, not collapsed back to page 1) and verified 95/95 passing. Final re-review confirmed the test is a genuine, non-vacuous regression guard (traced that it would fail if the hook's reset effect were keyed on `items` instead of `resetKey`) — Approved.

## Vocab Bank Polish (all 10 tasks + addendum whole-branch review + fix batch, commits ec82319..b212d4c) — COMPLETE, all re-reviewed clean. Final test count: apps/web 95/95, typecheck clean, build clean.

**Live manual verification (2026-08-15, done with the user):** user ran the app locally and confirmed the full flow works — full-width shell, multi-select filter combining, topic popover, scroll/page-bar behavior, and editing a real word (confirming Firestore `update` permission is actually granted, closing the one recommendation that couldn't be verified from source). User confirmed "ổn rồi" (all good). Plan fully done, nothing outstanding.

---

# LexiCore — React Web Plan 3 / Phase B (Part 1): Cài đặt (Settings)

**Design:** docs/superpowers/specs/2026-08-16-react-web-plan3-phase-b-settings-design.md
**Plan:** docs/superpowers/plans/2026-08-16-react-web-plan3-phase-b-settings.md
**BASE commit:** 80d171e (docs: add Cài đặt (Settings) implementation plan)

First of two ordered sub-specs for React Web Plan 3 Phase B (Settings, then Tra từ + Luyện tập). Settings goes first because neither of the other two screens can make repeated AI calls without a persisted BYOK key. 9 tasks: Cloud KMS backend (Tasks 1-2), web data layer (Task 3), UI components (Tasks 4-7), page assembly (Task 8), live GCP infra + deploy (Task 9, not subagent-dispatched). Executed via subagent-driven-development directly on `master`, same as every prior React Web plan.

## Status

- Task 1 (Cloud KMS service + `encryptApiKey` onCall function): complete (commit 3d7c1b0, 67/67 tests, typecheck clean, review clean — Approved). Reviewer verified the no-leak constraint directly (KMS errors wrapped in a generic `HttpsError`, original error discarded not interpolated) and confirmed the region-regression test matches the established per-function convention (`getPronunciation`/`generateContent`/`synthesizeSpeech`/`transcribeAudio`/`ping` all follow the same pattern). Implementer deviated from the brief's suggested Vitest mock construction for `@google-cloud/kms` (class-based mock instead of `vi.fn().mockImplementation()`, which isn't constructor-callable under this project's Vitest 4.1.10) — reviewer independently confirmed this matches pre-existing precedent (`cloudRunClient.test.ts`'s identical class-based mock of `GoogleAuth`) and that every assertion from the brief survived unchanged. 2 Minor findings logged, not fixed: KMS errors aren't logged server-side before being wrapped (matches existing `toHttpsError` convention elsewhere, not a regression — candidate for a codebase-wide logging pass later); whitespace-only `apiKey` input untested (low value, boundary already covered by empty-string case).
- Task 2 (`generateContent` Cloud KMS ciphertext support): complete (commit 212f9d5, functions 71/71 + apps/web 95/95 tests, typecheck clean both sides, review clean — Approved). Reviewer specifically verified the plan-author's own self-review fix (replacing a buggy `not.toHaveBeenCalled()` assertion — which would have spuriously failed since `generateContent.test.ts` accumulates mock call history across the whole file with no reset — with a before/after call-count delta) was carried through correctly by the implementer, and confirmed it's a genuine regression guard, not a weakened one. Confirmed all pre-existing tests untouched/still passing, KMS decrypt failures never reach the provider call, and the client/server duplicated-type sync comments are correct. 1 Minor finding logged, not fixed: `apps/web/src/lib/generateContent.ts`'s colocated test wasn't extended with an `apiKeyCiphertext` case (low value — the client function is a pure `httpsCallable` passthrough with no branching to exercise).
- Task 3 (`apps/web` settings data layer — modelPresets, settings CRUD, useSettings hook, encryptApiKey client): complete (commit 67fd874, 108/108 tests, typecheck clean, review clean — Approved). Largest single task in the plan (8 files). Implementer flagged a flaky failure mid-session in an unrelated pre-existing test (`vocab-bank/page.test.tsx` pagination timing) that reran clean twice; reviewer independently grepped for any import of this task's 4 new modules from the vocab-bank directory (zero matches) and confirmed the flake is genuinely out of scope for this diff. Reviewer confirmed the 4-file separation (static data / Firestore CRUD / React hook / callable wrapper) has no responsibility bleed, and that `useSettings.test.ts` exercises the real async lifecycle (logged-out fast path, error path, save round-trip) rather than happy-path-only. 3 Minor findings logged, not fixed, all narrow/currently-unreachable: `getSettings`'s provider merge is shallow (a partial per-provider doc would lose that provider's individual defaults — not reachable today since `saveSettings` always round-trips the full object); `getSettings` returns the shared `DEFAULT_SETTINGS` object by reference for logged-out/no-doc callers (risk only under a future in-place mutation); `useSettings`'s effect has no stale-response guard for rapid `uid` changes (e.g. fast logout/login racing two `getSettings` calls).
- Task 4 (`ModelPicker` component — preset dropdown + free-text custom model): complete (commit aec779f, 5/5 new tests, typecheck clean, review clean — Approved). Reviewer manually traced the `customMode` state fix (from the plan's own self-review, see plan commit) step-by-step through 6 render cycles and confirmed the dead-end bug it exists to prevent (custom input can never appear because visibility was derived from a `model` prop that can't change until the not-yet-rendered input fires `onChange`) does not regress — selecting "Khác..." genuinely reveals the input on the very next render, independent of the `model` prop. 1 Minor finding logged, not fixed, flagged forward for Task 5: `customMode` is plain local state with no reconciliation on prop change, so if Task 5 renders `<ModelPicker provider={active} .../>` without a `key={active}`, switching AI provider while mid-custom-entry would leave a stale custom input showing over the new provider's (possibly preset) model — controller is passing this to Task 5's dispatch as a `key`-based fix, not touching `ModelPicker.tsx` itself.
- Task 5 (`AiProviderSection` — provider/model/API key UI): complete (commits c84adaf..9da6cd6, 119/119 tests, review clean — Approved). First review returned "Needs fixes" — 1 Important finding: English UI labels ("AI Provider & API Key", "Provider", "API key") violating the plan's Vietnamese-only global constraint, traced to the *plan's own brief* (controller-authored bug, not an implementer deviation). Fix translated the 3 strings ("Nhà cung cấp AI & Khoá API"/"Nhà cung cấp"/"Khoá API") and updated the colocated test's label selectors. Re-review confirmed: all 3 strings translated in final file state, provider proper nouns (Gemini/Groq/OpenRouter) correctly left untouched, fix stayed surgical (encrypt-then-save logic, `key={active}` remount fix from Task 4, masked-placeholder, disabled-button all byte-identical to the already-approved pre-fix version). `ModelPicker`'s own "Model" label (Task 4, out of this task's file scope) was correctly left untouched by the fix — not yet flagged by any reviewer, noted for awareness only.
- Task 6 (`AppearanceSection` + `AppShell` theme/font-size wiring): complete (commit fc1a469, 126/126 tests across 28 files, typecheck clean, review clean — Approved). Widest-blast-radius task so far — modifies `AppShell`, which every real screen renders through. Reviewer independently re-verified (not just trusted the report) that no other screen's tests were put at risk: grepped for every `AppShell` reference in `apps/web/src`, confirmed it's only reachable via the untested `(app)/layout.tsx`, and cross-checked the reported 28-test-file count against the actual file count on disk. All `AppearanceSection` UI text confirmed Vietnamese (heading "Giao diện", labels "Chủ đề"/"Cỡ chữ", options Sáng/Tối/Theo hệ thống and Nhỏ/Vừa/Lớn) — the Task 5 English-label mistake was not repeated. 2 Minor findings logged, not fixed, both inherent to the plan's own client-effect-only design (not implementer deviations): a real (not theoretical) flash-of-wrong-theme on hard page load while `useAuthUser`/`useSettings` are still resolving, since there's no blocking inline script or SSR cookie; `zoom` CSS property is non-standard but broadly supported by this project's target browsers (Firefox added support in 2024).
- Task 7 (`AccountSection` + `DangerZoneSection`): complete (commit f437ba8, review clean — Approved). Smallest task in the plan; byte-for-byte match to the brief, zero scope creep. Vietnamese text re-confirmed correct (no repeat of Task 5's mistake). Reviewer verified `signOutOfFirebase` is a real export (not a broken/fabricated import) and that the sign-out test asserts a real mock call, not just button presence. 1 Minor finding logged, not fixed: `AccountSection` has no fallback for a null `displayName`/`email` (Firebase `User` fields are nullable) — deferred to Task 8 if needed, not required by this task's own brief.
- Task 8 (assemble the `/settings` page): complete (commits 832c609..733ca79, review clean — Approved). `next build` confirmed `/settings` is now a real route, resolving the sidebar link that had 404'd since React Web Plan 3 Phase A. Implementer correctly caught and fixed a brief-staleness bug on their own: the brief's page test still asserted `AiProviderSection`'s pre-Task-5-fix English heading text, corrected to the actual Vietnamese text and verified against the real component source. First review returned "Needs fixes" — 1 Important finding: the new `button.danger` CSS rule (bloom.css, for the Settings sign-out button) had equal specificity to a pre-existing, unrelated `.fa button.danger` rule and sat later in the file, winning the cascade tiebreak and silently restyling the Vocab Bank drawer's already-shipped "Xoá" (delete) button too (also `className="danger"`, matched both selectors) — a real, concrete, untested visual regression, not caught by any test since no CSS regression tests exist in this project. Fix renamed the Settings button's class to `btn-danger`. Re-review independently traced the cascade structurally (not just re-checked specificity/ordering) and confirmed the two selectors now key off fully disjoint class names — VocabDrawer's button still has class `danger` only, Settings' button has `btn-danger` only, zero shared selector surface, not a narrower fix that leaves an edge case.

## All 8 code tasks complete (Tasks 1-8) — Task 9 (live GCP infra + deploy + manual E2E verification) remains. Per the plan's explicit instruction, Task 9 is NOT dispatched to a subagent — it requires live `gcloud`/Firebase CLI access and human interaction, done directly with the user.

## Task 9 (live GCP infra) — steps 1-7 done directly with the user: Cloud KMS API enabled, keyring `lexicore-keys` + key `byok-api-keys` created in `asia-southeast1`, runtime SA confirmed live (`243190098866-compute@developer.gserviceaccount.com`, matches React Web Plan 2's notes), IAM `roles/cloudkms.cryptoKeyEncrypterDecrypter` granted, `functions/.env` updated with KMS config, `generateContent`+`encryptApiKey` deployed live and confirmed. Firestore security rules pulled directly from the live deployment via the Firebase Security Rules REST API (no `firestore.rules` file has ever existed in this repo — a gap flagged by multiple prior reviews, now actually resolved by reading the live rule instead of guessing): `match /users/{uid}/{document=**} { allow read, write: if request.auth != null && request.auth.uid == uid; }` — a recursive wildcard already covering the new `settings/config` doc with zero changes needed.

**Live manual verification with the user surfaced 2 real bugs before the checklist could be honestly marked passed** — both fixed as addendum tasks, same rigor (TDD, dispatch, review) as Tasks 1-8:

- **Task A (cross-component settings staleness):** `AppShell` (app-wide theme/font-size) and the `/settings` page each independently called `useSettings(uid)` — separate hook instances, no shared cache. Changing theme/font-size on the Settings page updated only that page's own local state (plus Firestore); `AppShell`'s separate instance never learned about the change, so the app-wide effect only applied after a full page reload. User found this live, not caught by any prior test (no test exercised two simultaneously-mounted consumers of the same hook). Fix: complete (commit c53284e, 136/136 tests across 33 files, typecheck clean, build clean, review clean — Approved). Introduced `SettingsContext`/`SettingsProvider`/`useSettingsContext` (`apps/web/src/lib/SettingsContext.tsx`), mounted once in `(app)/layout.tsx` above `AppShell`; both `AppShell` and `/settings` now read exclusively through the shared context. Reviewer traced this structurally (not just "does each file have a test"): confirmed the raw `useSettings(` hook has exactly one remaining call site (inside `SettingsProvider`), confirmed `SettingsProvider` is mounted exactly once, and confirmed the new `SettingsContext.test.tsx` genuinely proves single-instantiation (`useSettings` called exactly once) and cross-consumer sharing (two consumers under one provider reach the same `save`). Also fixed a pre-existing gap while touching the file: `(app)/layout.tsx` had no colocated test since React Web Plan 3 Phase A — added one that exercises the real, un-mocked `SettingsProvider`+`AppShell` wiring. Controller independently grepped `apps/web/src/app` to confirm `vocab-bank/page.tsx` (the only other real screen) doesn't duplicate the bug — it calls `useAuthUser` for its own sign-in gate (fine, Firebase's `onAuthStateChanged` is a live listener with no staleness risk) but never calls `useSettings` directly. 2 Minor findings logged, not fixed: `SettingsContextValue` manually re-declares `useSettings`'s return shape instead of `ReturnType<typeof useSettings>` (duplication risk if they drift); the sharing test proves cross-consumer sync via a triggered side effect rather than a direct reference-equality assertion (sufficient given the call-count test, but less literal).
- **Task B (Cài đặt has no Bloom visual design):** complete (commit 628fb7d + spacing fix 98ec259, 136/136 tests, review clean — Approved). The Settings screen shipped functionally complete but visually unstyled (bare HTML form controls, no card grouping, no spacing system) unlike every other screen's `.vb-*`/`.dh`/`.db`-style Bloom CSS — traced to a real plan-authoring gap (the Cài đặt design spec never extracted actual Bloom visual styling for these components, only reused generic `.scr-title`/`.btn-danger`). Fix was a pure additive-className + new-CSS-rules change (new `.settings-page`/`.settings-card`/`.settings-account-name`/`.settings-account-email`/`button.btn-primary` classes) — zero behavior/text/a11y changes, so zero test files needed touching, which the reviewer independently confirmed by checking the diff's file list contained no test files and no accessible-name-affecting changes. Reviewer specifically re-checked for the exact CSS-collision bug class Task 8 hit (grepped the new class names for pre-existing occurrences — none found; confirmed `button.btn-primary` doesn't collide with `.fa button`/`.fa button.danger` the way `button.danger` once did) and confirmed `AiProviderSection.tsx`'s stateful logic (`key={active}`, encrypt-then-save) was byte-identical, only the two intended classNames added. 1 Minor finding — the given CSS's `.settings-card label:last-of-type { margin-bottom: 0; }` rule doesn't work as intended because `ModelPicker` wraps its own "Model" label in a separate `<div>`, so it always independently qualifies as "last" and collapses the gap before the following "Khoá API" field — this was the plan-author's own CSS design flaw (not an implementer deviation), fixed directly by the controller (commit 98ec259, removed the rule entirely rather than trying to scope it more narrowly — leaves a small harmless extra margin below each card's true last field instead of a crowded gap), re-ran the full suite clean (136/136) before committing.
- **Task C (missing "Ngôn ngữ mục tiêu" / target language setting):** complete (commits 64e0072 + 3a2b369, 140/140 tests, review clean — Approved). Found by the user live: Flutter's Settings has a "Ngôn ngữ mục tiêu" picker (5 languages: Việt/Anh/Trung/Hàn/Nhật, `lib/features/dictionary/domain/entities/language.dart`'s `Language` enum, default English) used by the dictionary lookup feature, completely absent from the web Cài đặt design — another real scope gap from the original plan, not just a bug. Added `targetLanguage: TargetLanguage` to `UserSettings` (default `"english"`) and a new `LanguageSection` component between `AccountSection` and `AiProviderSection`. Reviewer did not accept "labels look right" — ran a programmatic codepoint-by-codepoint diff of all 5 `LANGUAGE_LABELS` values (including the 3 non-Latin scripts, 中文/한국어/日本語) against the Dart enum's `label` getter specifically (not `code`/`ttsLocale`, which share the same enum-case names and could be confused) — all exact matches. Also independently traced `getSettings`'s merge logic against a synthetic pre-existing Firestore doc with no `targetLanguage` key at all (the real shape of every production doc written before this field existed) and confirmed it correctly falls through to the `"english"` default, matching the implementer's claim. 1 Minor finding — that exact fallback scenario was traced/claimed but never actually asserted in the test suite — fixed directly by the controller (commit 3a2b369, one-line regression assertion added to the existing merge test), re-verified passing before committing.

## Task 9 + all 3 live-QA addendum tasks (A, B, C) complete. Full web suite: 140/140 tests across 35 files, typecheck clean, build clean.

**Two more live-QA follow-ups (2026-08-16), both handled directly by the controller (no subagent — trivial/documentation-only):**
- **2-column layout** (commit 0f9d9bc): user found the single-column `.settings-page` (capped at 620px) left most of the wide `.app-frame` empty. Switched to a 2-column CSS grid (`max-width: 980px`, `grid-template-columns: 1fr 1fr`), page title spans both columns via `grid-column: 1 / -1`. Pure CSS change, no JSX/test changes needed. 140/140 tests still pass.
- **Per-language `vocab_records` collections — decision recorded, NOT implemented**: user wants `users/{uid}/vocab_records` (one flat collection today, ~290+ real records) split into one Firestore subcollection per target language, now that Cài đặt has the new "Ngôn ngữ mục tiêu" setting. Explicitly scoped to `vocab_records` only (`topics` stays shared). User explicitly chose to record this as a spec decision now rather than implement/migrate real data in this pass — documented in `docs/superpowers/specs/2026-08-11-react-web-redesign-design.md` §9 and in memory (`per_language_vocab_records.md`) with the full list of what implementation will require later: a `getVocabRecords(uid, language)` signature change, a real-data migration script, and a matching Flutter-side change (`vocab_repository_impl.dart`) since both apps share the same Firestore data — needs its own spec → plan cycle before implementation.

Remaining: final live re-verification with the user of the original Task 9 checklist plus these follow-ups — confirm theme/font-size apply without reload, confirm the Settings screen now has real Bloom styling in a 2-column layout, confirm the new Ngôn ngữ mục tiêu field saves/persists correctly.

**Live re-verification (2026-08-16, done with the user): confirmed "ok rồi"** — theme/font-size apply without reload, Bloom styling + 2-column layout both correct, Ngôn ngữ mục tiêu field present and working.

## Final whole-branch review (80d171e..0f9d9bc, 16 commits, reviewed on Opus): Ready to merge: With fixes.
Reviewer independently verified every named cross-task interaction against current file state (not per-commit diffs): `SettingsContext` single-mount point, the Cloud KMS encrypt→decrypt round trip never reaching the provider on failure, `ModelPicker`'s `key={active}` fix still present, CSS layering across 3 successive changes composing cleanly, Vietnamese text held everywhere, `targetLanguage` merge-default correctness. No Critical findings.
4 Important findings, all fixed in one dispatched batch + directly by the controller:
- `functions/.env`, the progress ledger, and the master spec's §9 addition were never actually committed — HEAD couldn't deploy working functions (`encryptApiKey` would throw "Missing Cloud KMS configuration"). Fixed directly by the controller (commit f56805e) before dispatching the rest of the batch.
- **Credential-misrouting bug**: `AiProviderSection`'s `keyDraft`/`error` weren't scoped to the active provider — typing a key for one provider then switching providers before saving would silently encrypt and store that key under the *new* provider. Fixed (commit a012ce9): implementer found the originally-specified `useEffect([active])`-only approach couldn't actually close the window in practice (in the real app, `active` only changes after a Firestore round-trip repopulates the `settings` prop — a window during which a stale draft could still be submitted) and added an imperative clear directly inside the provider `<select>`'s `onChange`, closing the bug the instant the dropdown changes rather than waiting on a prop update. Re-review independently verified this is strictly stronger than the original spec, not a rationalization — traced the exact original bug scenario against the current code and confirmed it's closed via two independent mechanisms (the imperative clear, and the disabled-button guard).
- **KMS ciphertext not bound to the owning user**: `encryptWithKms`/`decryptWithKms` took no Additional Authenticated Data, so a ciphertext wasn't cryptographically tied to the user it was created for (Firestore rules prevented exploitation today, but this removed a defense-in-depth layer for the single most sensitive value in the system). Fixed (commit 498aecb): both functions now require an `aad` parameter; `encryptApiKey`/`generateContent` both pass `request.auth.uid`. Re-review confirmed the same uid is used on both sides of the round trip (required for it to work at all) and that `kms.test.ts` asserts the exact AAD value via whole-object `toHaveBeenCalledWith`, not just a call-count check. **Breaking change, expected and accepted**: the one API key already stored in production (the developer's own Gemini key, from Task 9's manual verification) needs to be re-saved in Cài đặt after this deploys — old ciphertexts can't be migrated (would require the raw key, defeating the point of KMS).
- `AppearanceSection`/`LanguageSection` silently swallowed Firestore write failures (`void onSave(...)` with no `.catch`) — a failed save just snapped the UI back with no message. Fixed (commit 492d721) with the same local-`error`-state pattern `AiProviderSection` already had.
5 Minor findings, 2 fixed directly by the controller (commit 58f8f25, docs/CSS only) and 2 more fixed in the same dispatched batch (commits a7e0893 `AccountSection` null-fallback, a1896e9): the master spec's §7 Key Decisions table still contradicted the already-recorded §3.5 BYOK reversal; a stray double blank line left from an earlier CSS edit; the sign-in/error/loading branches of `settings/page.tsx` reused the 2-column `.settings-page` grid class meant for the 5-card loaded screen; `AccountSection` had no fallback for a null `displayName`/email. 3 further Minors logged, not fixed: `apiKeyCiphertext`'s decrypt path has never run against real KMS yet (nothing calls `generateContent` with a ciphertext until the next sub-spec builds Lookup/Practice hub — worth a one-off manual check before that work starts, not now); `fs-large`'s `zoom: 1.15` combined with `.app-frame`'s `min-height: calc(100vh - 48px)` produces a spurious vertical scrollbar (needs a bigger redesign — a font-size custom property instead of `zoom` — not a quick fix); the encrypt/decrypt error alert shown to the user is in English (`HttpsError` messages aren't translated) despite the Vietnamese-only constraint.

**Fix batch re-review (58f8f25..a1896e9, 5 commits, reviewed on Opus): Sound, Ready to merge: Yes.** Reviewer specifically verified the implementer's Finding-#1 deviation from spec was a genuine improvement (traced the non-optimistic `useSettings.save` to confirm the retained `useEffect` couldn't wipe a freshly-set error, ruling out the one way it could have conflicted with the new imperative clear) and confirmed the KMS AAD values match on both the sole encrypt and sole decrypt call site in the whole codebase (grepped to confirm no other call sites exist). 3 further Minors logged, 2 fixed directly by the controller (commit 608eca2 — stale comment corrected, `authLoading` branch given the missing "Cài đặt" title matching the other 3 non-loaded states), 1 not fixed (a friendlier "khoá API đã bị xoá" hint after a failed provider-switch clears the draft — UX nicety, not a bug).

## React Web Plan 3 Phase B Part 1 (Cài đặt / Settings) — COMPLETE. Design spec, plan, all 8 original tasks, 3 live-QA addendum tasks (A/B/C), a 2-column layout fix, a per-language-vocab-records spec decision (documented, not implemented), final whole-branch review + fix batch + re-review — all done, all re-reviewed clean. Final counts: apps/web 147/147 tests (2 known-flaky pagination-timing tests under heavy machine load, unrelated to this work, independently re-verified passing in isolation multiple times throughout this branch), functions 71/71 tests, both typechecks clean, production build clean. Live-deployed and manually verified end-to-end by the user, including the theme/font-size cross-component sync fix, the Bloom-styled 2-column layout, and the new Ngôn ngữ mục tiêu field.

## React Web Plan 3 Phase B Part 2 (Tra từ / Lookup + Ôn tập / Practice, full-flow) — spec + plan complete, execution not yet started.

Brainstormed (including 4 live visual-companion iterations to finalize the flashcard flip mechanic — settled on a diagonal `rotate3d(1,1,0,...)` hinge with a monotonically-increasing rotation counter, "flashcard-v4-360.html"), spec written and committed (`docs/superpowers/specs/2026-08-16-react-web-plan3-phase-b-part2-lookup-practice-design.md`), and a 12-task implementation plan written and committed (`docs/superpowers/plans/2026-08-16-react-web-plan3-phase-b-part2-lookup-practice.md`).

Key decisions baked into the plan: Ôn tập is **zero-AI** (pure SM-2 flashcard review, deliberately diverging from Flutter's ~70%-AI-generated-exercise behavior — user's explicit simplification call); Lookup's save-to-Vocab-Bank flow reuses `EditVocabModal` in a new "create" mode, edited in-place on the Lookup screen itself; sentence lookups stay translation-only, never saveable (matches Flutter exactly); SM-2 is batch-computed and written only at the session result screen (Task 12), with every per-word result already carrying `vocabRecordId`+`quality` so a future streak/stats feature can hook in without refactoring; sidebar "Luyện tập" renamed to "Ôn tập" (Task 6).

12 tasks: (1) Lookup domain logic — `parseAiJson.ts`, `inputDetector.ts`, `lookup.ts`; (2) Vocab Bank data-layer additions — `getVocabRecordByHeadword`, `saveVocabRecord`; (3) `EditVocabModal` create mode; (4) Lookup page search+display; (5) wire the save flow into Lookup; (6) sidebar rename; (7) SM-2 compute (`sm2.ts`) + `updateVocabRecordSm2`; (8) practice session word-pool selection (`practiceSession.ts`); (9) `FlashcardCard` component; (10) `/practice` setup phase; (11) `/practice` session review loop; (12) `/practice` result screen + batch SM-2 write. Self-review (spec coverage, placeholder scan, type consistency across all 12 tasks) done inline, no gaps found.

**Next up:** dispatch Task 1 (Subagent-Driven execution, matching Part 1's pattern) once the user confirms execution approach. Still outstanding, deferred by explicit user decision: Dashboard + streak collection (its own later phase), Flutter-side sync of both the streak collection and the settings doc, and the per-language `vocab_records` collection split (documented in the master spec §9, needs its own spec → plan cycle).

Task 3: complete (commit f247db4..e103c27, review clean)

Task 4: complete (commit e103c27..59eef67, review found 1 Important — missing settings-loading gate causing a silent no-op click window, baked into the brief itself, fixed directly by the controller in 3 further commits: 32c5dcb pre-existing Task-2 typecheck fix found by the implementer, d47d76e the settings-loading gate). 3 Minor findings logged, not fixed: raw English error text on generateContent failure (pre-existing app-wide convention), search input has no label/aria-label, synonym chip React key could collide on duplicate AI output.

Task 5: complete (commits d47d76e..4680036, review found 1 Important — save-button-absence tests were mislabeled/hollow, fixed in commit 4680036, re-review clean). 2 Minor findings logged, not fixed: preselectTopicIds has no dedup guard against duplicate AI-suggested topic names, buildDraftRecord is called twice per save action (harmless duplicate work).

Task 6: complete (commit 4680036..896468d, review clean)

Task 7: complete (commit 896468d..0387651, review clean — SM-2 formula independently verified branch-by-branch against compute_sm2_use_case.dart, no discrepancy; 2 implementer-flagged deviations (mock-leak test fix, updateDoc spread for a Firestore UpdateData typing quirk) both independently confirmed legitimate)

Task 8: complete (commits 0387651..c5611c3, review found 1 Important — shuffle() had zero test coverage capable of detecting an identity-function regression, fixed in commit c5611c3 with a Math.random-pinned deterministic test, re-review verified the hand-traced permutation independently, clean). 2 Minor findings logged, not fixed: no explicit empty-records test, no explicit count-larger-than-pool test (both trivially correct by inspection).

Task 9: complete (commit c5611c3..8f51b5b, review clean — rotation/showingFront math hand-traced correct at 0/180/360/540, click-gating and peek-vs-grade separation verified, record.id independence confirmed for Task 11 no-key reuse, CSS collision-free. 1 pre-existing unrelated test flake confirmed (vocab-bank pagination-timing tests, already documented). 2 Minor findings logged, not fixed: no explicit re-click-while-flipped-is-noop test, asymmetric JS guard between front/back handlers (relies on CSS backface-visibility, standard idiom).

Task 10: complete (commit 8f51b5b..b734ffe, review clean — setup-phase-only scope confirmed, TopicFilterPopover usage verified against real source, reactive preview count real-tested). 2 Minor findings logged, not fixed: authLoading branch omits the scr-title wrapper (matches brief verbatim), preview count reruns the Fisher-Yates shuffle every render just to read .length.

Task 11: complete (commit b734ffe..20f107c, review clean — critical no-key constraint on FlashcardCard verified with certainty, off-by-one session-completion logic traced correct at both boundaries, Math.random test pin confirmed legitimate/precedented not masking). 1 Minor logged, not fixed: randomSpy.mockRestore() not wrapped in try/finally, low practical impact given current file contents.

Task 12: complete (commit 20f107c..bfbc202, review clean — exactly-once write guard verified (ref set before async work, reset in handleStart for a second session), single shared now confirmed, no SM-2 reimplementation, per-word write failures independent/non-blocking via individual .catch). 2 Minor findings logged, not fixed: batch-write test asserts only a partial Sm2Fields via objectContaining rather than the full object, console.error is English (dev-facing log, not UI).

## All 12 tasks complete. Proceeding to final whole-branch review.

## Final whole-branch review (d0a7c6f..bfbc202, 16 commits, reviewed on Opus): Ready to merge: With fixes.

Reviewer independently verified the SM-2 port against the Dart source again at whole-branch scope, confirmed the sentence-never-saveable constraint is enforced at 3 independent layers, confirmed zero-AI-in-Ôn-tập and single-SM2-write-site hold app-wide (grepped the whole src tree), and confirmed "Ôn tập" naming is consistent everywhere. No issues with per-task work standing alone.

1 Critical, found only at whole-branch scope (no single task diff could see it): `saveVocabRecord` wrote new vocab_records documents with no `id` field in the body. Flutter's sync_service.dart caches the raw doc into Hive and does a non-nullable `json['id'] as String` cast when decoding it (both in `_buildHeadwordIndex`, called OUTSIDE startSync's try/catch, and in every VocabRecord.fromJson call site) — a single word saved from the web would crash Flutter sync and poison the entire Vocab Bank/practice/reading/listening word lists on next mobile launch, until deleted. This was a plan defect (the plan itself prescribed the id-less write), faithfully implemented and missed by the Task-2 reviewer because nothing in that task's diff alone revealed the cross-app contract. Fixed directly by the controller (commit 1299deb): `setDoc(ref, { ...record, id: ref.id })`, test tightened to assert the full written shape. Re-review independently traced the Dart-side crash path end-to-end and confirmed the fix closes it.

2 Important, both fixed directly by the controller:
- No duplicate-save guard: the AI can return a re-cased/re-lemmatized headword different from the user's raw query, so the lookup-time cache-check can miss an existing record and create a duplicate on save. Fixed (commit 4cf3072): handleSaveNewRecord re-checks getVocabRecordByHeadword immediately before writing; on a hit, sets existingRecord and skips the write. Re-review confirmed this is the correctly-scoped minimum fix (full case-insensitive matching needs a Flutter-side headwordLower schema addition, out of scope) and that the normal create path is undisturbed.
- Stale local `records` after the result screen's batch SM-2 write: "Ôn tập lại" re-selected from the pre-session snapshot, so a just-reviewed word still looked due and a repeat grade would compute SM-2 from its stale base, silently overwriting the just-written progress. Fixed (commit 7d69b1f): the write effect now merges computed Sm2Fields into `records` state alongside the Firestore write. Re-review confirmed the exactly-once write guard and effect dependencies are undisturbed, untouched records keep referential identity, and the fix resolves the reported symptom via selectSessionWords' due-filter.

Re-review of all 3 fixes (bfbc202..7d69b1f, reviewed on Opus): Ready to merge: Yes. Flagged one operational (non-blocking) follow-up: scan production users/{uid}/vocab_records for any id-less docs written during manual testing of this branch before/around merge, since the fix is write-path-only and does not remediate documents already written pre-fix. Also logged, not fixed: no regression test added for Fix 2 or Fix 3 (only Fix 1 tightened); a duplicate-hit silently discards the user's in-modal edits with no message; the "concurrent save from another tab" comment on Fix 2 overstates what a non-transactional read-then-write actually guarantees; Fix 3's local merge is optimistic (applies even if the Firestore write itself later fails, only console.error'd).

## React Web Plan 3 Phase B Part 2 (Tra từ / Lookup + Ôn tập / Practice) — COMPLETE.
All 12 tasks implemented, individually reviewed (11 clean or fixed-then-clean at task scope, 1 Critical + 2 Important found only at final whole-branch scope and fixed). 16 task/fix commits + 3 final-review fix commits = 19 commits total on top of the plan doc commit. Ready to merge per two independent final reviews.

Final verification (2026-08-17): apps/web typecheck clean, build clean (/lookup and /practice routes present), full test suite 209/211 passing (2 known-flaky pagination-timing tests, independently re-confirmed passing in isolation, unrelated to this work — same pre-existing flake documented under Phase B Part 1). All 19 commits already on master (no separate feature branch was used, matching Part 1's pattern). Not yet deployed/live-tested by the user.

## Live-testing follow-up fixes (2026-08-17, post-completion, all on master):
- Topic pre-selection in Tra từ was strict-equality-only, missing AI phrasing variants ("food and drink" vs "Food & Drink") and could push duplicate topic ids — loosened to normalized matching + dedup (commit 51a6248).
- Multi-sense meanings (e.g. "recommend": to suggest vs. to advise) had no delimiter when the AI's prompt only covered cross-part-of-speech senses, rendering as one garbled string — broadened the prompt + added splitMeaningSenses() so both Lookup and FlashcardCard render each sense on its own line (commit 55afc0f).
- Added "Khám phá từ mới" (discover a new word) to Tra từ, porting Flutter's lookup_provider.dart discover()/gemini_dictionary_source.dart discoverWord() — a sparkle button that asks the AI for a word with no query typed, fills the search box, and runs the normal cache-check-then-lookup flow (commit 3c5e244).
- Ôn tập result screen: split the single "Ôn tập lại" button into "Về Ôn tập" (back to setup) and "Ôn tập lại ngay" (calls handleStart() directly, reusing the exact filters already in state — no need to re-pick); restyled the CEFR/word-count <select>s to match the Topic filter's chip look + active-state highlight (commit d00f0bc).
- A screenshot the user shared showing a blank/unstyled Ôn tập session screen and a stale sidebar label ("Luyện tập") turned out NOT to be a code bug — curled the running localhost:3000 dev server directly and confirmed it already serves the correct "Ôn tập" label and fully-bundled Bloom CSS (.fc-card, .practice-progress-row, etc. all present in the served chunk). Diagnosed as a stale browser tab; told the user to hard-refresh. Worth remembering: this dev server auto-picks up file changes correctly, so a user-reported "still looks old" complaint should default to a browser-cache explanation before assuming a code regression, when the server itself can be curled to check.

## Live-testing follow-up round 2 (2026-08-17/18, all on master):
- Merged Khám phá's 2 AI calls into 1 (buildDiscoverPrompt now returns word+full entry together) — user flagged the extra AI-cost/latency directly (commit 303f0d3).
- Fixed .practice-select's default black browser focus outline, themed to match the rest of the app (same commit).
- Added pronunciation playback (🔊) to both Tra từ and Ngân hàng từ vựng, wiring up the getPronunciation Cloud Function (built in React Web Plan 2, never called from the web client until now) via a new apps/web/src/lib/pronunciation.ts wrapper + reusable PronunciationButton component (commit f8d85fd). Only vi/en have deployed Piper voices — button silently hides for chinese/korean/japanese records rather than offering a call that would fail.

Full round-2 fix list from this live-testing session: topic pre-selection loosened + deduped (51a6248), multi-sense meaning display + prompt broadened (55afc0f), Khám phá từ mới added then merged to 1 AI call (3c5e244, 303f0d3), Ôn tập result screen split into 2 actions + dropdown Bloom restyle + focus fix (d00f0bc, 303f0d3), pronunciation playback added to both screens (f8d85fd). All typecheck clean, full suite 235/235 passing (0 flakes this run), production build clean.

## Live-testing follow-up round 3 (2026-08-18, all on master):
- Replaced Ôn tập's native <select> CEFR/word-count dropdowns with a reusable SimpleDropdown component (same vb-chip trigger + floating panel pattern as TopicFilterPopover) — native selects couldn't be restyled past the OS-rendered open-list chrome (blue highlight, black focus ring), which the user screenshotted as clashing with the rest of the page (commit 7b0c5aa).
- Extended pronunciation playback (🔊) to VocabDrawer (the Vocab Bank detail view) — headword/IPA + each example — the third place after Tra từ and EditVocabModal (commit 7575089).

Full round-3 fix list: SimpleDropdown (7b0c5aa), VocabDrawer pronunciation (7575089). All typecheck clean, full suite 241/241 passing (0 flakes this run), production build clean.

## Live-testing follow-up round 4 (2026-08-18, all on master):
- User explicitly asked: "I want ALL dropdown spots to have the same UI as the Chủ đề select" — converted every remaining native <select> in the app (Cài đặt's target language, theme, font size, AI provider, model picker) to SimpleDropdown (commit b70504b). Only /dev/verify's GenerateContentPanel keeps a native select, left alone as an internal diagnostic page.
- Non-obvious bug hit mid-conversion: wrapping a SimpleDropdown's trigger <button> in a <label> (as the old <select>s all were) overrides the button's accessible name with the label text, since <button> is a labelable element per the HTML accname spec — every trigger's computed name became the field label ("Ngôn ngữ đang học") instead of its own visible text ("English ▾"). Fixed by using a sibling `.settings-field` div + `<span>` instead of `<label>` wrapping wherever the control became a SimpleDropdown; native `<input>`s (API key, custom model name) kept real `<label>` wrapping since they don't have this problem. Worth remembering for any future custom-button-as-form-control component: `<label>` wrapping ANY labelable element (button included, not just input/select) claims its accessible name.

All 5 Settings dropdown tests rewritten for click-open-then-click-option interaction instead of fireEvent.change. Typecheck clean, full suite 241/241 passing, production build clean.

## Live-testing follow-up round 5 (2026-08-18, all on master):
- User called out that SimpleDropdown was not actually reusing vb-topic-popover — it had its own invented vertical list-menu look (simple-dropdown-panel/opt) instead of the real wrapped-chip-grid Topic filter markup. Fixed to render its panel as literal `.vb-topic-popover` > `.vb-topic-popover-opts` > `.vb-chip` buttons, byte-identical structure to TopicFilterPopover, and deleted the dead custom CSS (commit d379c83). Lesson: when asked to make something's UI "giống hệt X" (identical to X), reuse X's actual DOM structure/classes directly rather than approximating the visual with new CSS — an approximation can drift from the real thing in ways that are obvious to the user but easy to miss in code review.

Typecheck clean, full suite 241/241 passing, production build clean.

## React Web Plan 3 Phase C Part 1 (Đọc & gõ) — execution started 2026-08-18 via subagent-driven-development. Base commit a1b97fa. Plan: docs/superpowers/plans/2026-08-18-react-web-plan3-phase-c-reading-typing.md (10 tasks).

Task 1: complete (commits a1b97fa..38d5531, review found 1 real gap — prompt never told the AI what CEFR level to target despite the setup screen already having that filter value — fixed directly by adding a 3rd maxCefr parameter, plan text updated to match before Task 8 dispatch). 1 Minor logged, not fixed: brief/test code was a verbatim transcription with no independent test-design judgment (expected for a tightly-specified port task).

Task 2: complete (commits e58185e..6d1ed24, review found 1 Important — upper finalScore clamp boundary never tested, fixed in commit 6d1ed24, re-review confirmed the new test genuinely exercises Math.min(1,...)). 1 Minor logged, not fixed: multi-sentence aggregation test only checks overallAccuracy, not the other 3 fields for the same input.

## React Web Plan 3 Phase C Part 1 (Đọc & gõ) — execution log (retroactively reconstructed 2026-08-20, see incident note below)

Task 1: complete (commits 9fa3d95..38d5531, 2026-08-18 — review found a real gap: buildReadingPassagePrompt needed an explicit maxCefr instruction, not just implied difficulty from the word list; fixed same-day). Plan doc's own Task 1 section was never updated with this fix (only Task 8's downstream reference was) — see incident below.
Task 2: complete (commits 3b81567..6d1ed24, 2026-08-18 — review found aggregateSentenceStats' upper Math.min(1,...) clamp was never exercised by any test; added one test, no source change).
Task 3: complete (commit 365c9f0, 2026-08-18 — approved clean, no fixes).

**INCIDENT (2026-08-20):** This conversation resumed today after a gap (2 real days) with "tiếp tục". No ledger entries existed yet for Tasks 1-3 (the 2026-08-18 session ended before writing them), so the resume re-dispatched Task 1 from scratch. Because the plan doc's Task 1 section still had the pre-fix 2-arg signature (see above), the fresh implementer regenerated the OLD version, regressing apps/web/src/lib/readingPassage.ts from the correct 3-arg (maxCefr) form back to 2-arg — commit f83a7b1. Caught immediately by inspecting the review-package diff (showed 7 commits instead of the expected 1) before dispatching the task reviewer. Fixed: git revert f83a7b1 (commit 5b87754, verified clean 10/10 readingPassage tests + tsc), then corrected the plan doc itself (commit 338bd43) so Task 1's own section matches what actually shipped, and retroactively marked Tasks 1-3 complete in both the plan checkboxes and this ledger. Full suite re-verified 271/271 passing after the revert, before resuming at Task 4.

**Lesson:** when a task-review finds a fix that changes a function's own signature/behavior, the fix must update THAT task's own section in the plan doc, not just downstream tasks' "Consumes" notes referencing it — otherwise a future resume (especially after a context/session gap) can regenerate the pre-fix version verbatim. Also: always write the ledger entry for a completed task in the SAME message as marking it complete, not deferred to "later" — the entire failure mode here was a session ending before that write happened.

Task 4: complete (commit 4e6dce2..6387af4, review clean — verified byte-for-byte faithful extraction, lookup/page.test.tsx confirmed untouched, behavior equivalence traced field-by-field). 1 Minor logged, not fixed: the cap-at-2 test fixture only has 2 distinct topics so doesn't truly exercise the cap-triggering branch — originates in the brief itself, not an implementer deviation.

Task 5: complete (commit 6387af4..4f61c80, review clean — byte-identical to the brief, design constraints (plain input + separate color span, no contentEditable, no future-sentence leakage, no vocab highlighting) all verified structurally). Content was already present on disk from earlier work, implementer verified+tested+committed rather than rewriting. 2 Minor findings logged, not fixed: smoke-test-only assertion for no-future-sentence-leakage, typed.split("") wont handle multi-codepoint chars correctly (non-issue for current English-only passage text).

Task 6: complete (commits 4f61c80..1f0e3d0, review found 1 Important — handleSaveAll silently swallowed a mid-batch error with zero user feedback, fixed in commit 1f0e3d0 with try/catch + surfaced alert + preserved partial-save state, re-review verified with a genuine 2-item-batch-fails-on-item-2 test). Both implementer-flagged deviations (span-wrap for RTL text matching, pre-existing unscoped .link-btn CSS gap) confirmed real/legitimate on independent check. 3 Minor findings logged, not fixed: unstyled bulk-save error paragraph (matches pre-existing pattern), reused empty-state message for zero-suggestions vs all-dismissed, no direct test for duplicate-skip on the single tap-to-save path (logic is shared/symmetric with the tested bulk path).

Task 7: complete (commit 1f0e3d0..fb2a3cf, review clean).

Task 8: complete (commit fb2a3cf..e5bfd6b, review clean — buildReadingPassagePrompt 3-arg call independently re-verified against the live readingPassage.ts, min-words gate confirmed to use an untruncated count via a deliberately separate selectSessionWords call). 2 Minor findings logged, not fixed: test suite (inherited from the brief) varies behavior only via mock data not simulated UI interaction with the dropdowns, loadError surfaces raw err.message which could be non-Vietnamese (pre-existing pattern copied from /practice).

Task 9: complete (commit e5bfd6b..576c649, review clean — deletion-tracking local-variable pattern hand-traced correct for the completing-keystroke-is-itself-a-deletion scenario, session-state reset/off-by-one boundary/partial-match-non-advancement/zero-SM2-writeback all verified). 1 Minor logged, not fixed: same-length select-all-retype registers zero deleted chars (inherent limitation of length-diffing, also present in the ported Flutter logic, out of scope).

Task 10: complete (commit 576c649..5135833, review clean — 4 stat cards, vocab-used matching, VocabSuggestionsSection props, "Sinh bài mới" reset-vs-regenerate distinction, real button vs Link for "Về trang chính", ReadingSessionResult confirmed type-only/never constructed, zero SM-2 writes all independently verified). No stub comments remain, genuinely terminal task. Test fix (getAllByText for a legitimate two-card 100% collision) confirmed a real bugfix not a weakened assertion.

## All 10 tasks of React Web Plan 3 Phase C Part 1 (Đọc & gõ) complete. Proceeding to final whole-branch review.

## Final whole-branch review (d0a7ce4..5135833, 20 commits — scoped to Đọc & gõ work from 9a56b0e onward, reviewed on Opus): Ready to merge: With fixes.

Reviewer independently re-verified the Task 1 incident is fully resolved (3-arg signature confirmed live, exactly 1 call site, no stale references anywhere), zero SM-2/streak writes confirmed by grep not claim, phase-state threading correct on both the reset-to-setup and fresh-generate paths (belt-and-braces: both handleNewPassage AND handleGenerate independently clear all 6 session fields), VocabSuggestionsSection confirmed genuinely reusable (no reading-specific coupling), and buildVocabRecordDraft confirmed identically used by both its original (Tra từ) and new (VocabSuggestionsSection) call sites. Independently re-ran typecheck (clean) and full suite (54 files / 304 passing) rather than trusting task reports.

4 Important findings:
- Plan doc had Tasks 4-10 still unchecked/undated despite being complete, with completion only recorded in the previously-uncommitted ledger — reviewer flagged this as re-arming the exact precondition that caused the Task 1 incident. Fixed directly by the controller (commit f277826): all 10 tasks now carry ALREADY IMPLEMENTED + commit SHA markers, all steps checked, ledger committed.
- `.link-btn` ("Lưu tất cả"/"Thử lại" in VocabSuggestionsSection) had no CSS rule outside EditVocabModal's scoped `.modal-field button.link-btn`, rendering as unstyled default buttons on the result screen's primary call-to-action row — inherited verbatim from the plan's own prescribed code. Reviewer explicitly recommended fixing now over deferring (cheap, high-visibility). Fixed (commit 41ebea0): added an unscoped base `.link-btn` rule, kept the modal-specific `align-self` override scoped separately so EditVocabModal's existing "+ Thêm ví dụ" button is unaffected.
- `handleSaveAll` had no in-flight guard — two overlapping invocations (e.g. a double-click during a 10-item batch) could both pass the per-item duplicate check for the same headword before either write completed, creating duplicate vocab_records. Fixed (commit 41ebea0): added `bulkSaving` state, guards entry, disables the button with "Đang lưu…" label during the operation, resets in the existing finally alongside the already-shipped error-surfacing fix from Task 6's own review.
- **Accuracy stat is architecturally pinned to 100%**: computeSentenceStats only ever runs on the exact keystroke where typed===target (by construction), so overallAccuracy is always 1 and finalScore reduces to a pure deletion-penalty score. Reviewer traced this to Flutter's reading_practice_provider.dart (identical structure) and the design spec's own §3.2 wording ("index-wise match count against the target at completion time") — a faithful port of an already-approved spec decision, not an implementer bug. **Not fixed — surfaced to the user as a design decision**, not unilaterally redesigned during a review-fix pass.

12 Minor findings logged, not fixed (representative subset): upcoming sentences never shown (spec says "upcoming dimmer", current impl only shows completed+current — may be intentional simplification, worth confirming); typing placeholder hardcoded to "tiếng Anh" regardless of target language; single-save duplicate path silently discards the user's just-made edits instead of switching to the existing record (Tra từ's equivalent does switch); bulk-save does up to 10 sequential Firestore round-trips when existingRecords is already available for a local pre-check; selectSessionWords reruns shuffle every setup-phase render just for .length; ~30 lines duplicated verbatim between practice/page.tsx and reading/bilingual/page.tsx (CEFR/word-count constants, Phase type, load effect) — recommended extracting before Part 5/6/7 copies it a 3rd time; parseVocabSuggestions hardcodes inputType:"word" even though the prompt allows phrases; records never refetched after saving suggestions (won't count toward the min-5 gate until reload); no test for a second clean session after "Sinh bài mới" (verified correct by reading, not test-locked).

**Recommendations logged for future sub-specs**: extract a shared session-setup surface (constants + dropdown options + Phase type + load effect) before Part 5/6/7/Nghe each copy it again; consider a lint/test check connecting className strings to bloom.css rules (would have caught .link-btn); move formatDuration out of the component into readingScoring.ts alongside the other pure helpers.

## React Web Plan 3 Phase C Part 1 (Đọc & gõ) — COMPLETE

All 10 tasks implemented, individually reviewed (9 clean or fixed-then-clean at task scope, all clean), 1 real incident (Task 1 stale re-dispatch) caught and fully resolved mid-execution, final whole-branch review found 3 Important issues (2 fixed, 1 surfaced as a design decision) + 12 Minor (logged). Independently re-verified: typecheck clean, full suite 305/305, production build clean (9 routes prerendered).

**4th Important finding resolved (commit 3d6e2c4):** offered the user 3 options for the always-100%-accuracy finding (keep as Flutter-parity, track peak mistakes for a real signal, or drop the card) — user chose to implement real tracking. Added `countMismatches()` to readingScoring.ts and a live-tracked `mistakeChars` peak per sentence (same caller-tracks-it-across-keystrokes pattern as the existing `deletedChars`), aggregated into a new `typingAccuracy` field. The result screen's "Độ chính xác" card now reads `typingAccuracy` instead of the always-1 `overallAccuracy`; `overallAccuracy`/`finalScore`/`deletionRatio` are untouched (finalScore's spec-defined formula still uses overallAccuracy, deliberately not touched — that wasn't part of the ask). Added a new test simulating an in-place typo-then-correction (same length, so deletedChars stays 0) verifying the card shows 67% not 100%. Re-verified independently: typecheck clean, readingScoring.test.ts + bilingual page.test.tsx 30/30, full suite 309/312 (3 failures are the same pre-existing vocab-bank pagination test timeouts under full-suite CPU contention — confirmed by passing 19/19 in isolation, unrelated to this change).

Branch considered done. Direct-to-master workflow (no feature branch/PR in this repo), so `finishing-a-development-branch`'s merge/PR menu doesn't apply — reported status directly instead, matching the pattern from the end of the prior Ôn tập plan.

## Saved Reading Exercises (Đọc & gõ pilot) — execution log

Task 1: complete (commits 1b04537..05a6b77, review clean - matching semantics topic-overlap/CEFR-at-or-below/word-count-exact-null-match/excludeId/random-among-multiple all independently re-verified as real assertions not mock theater, vocabIds confirmed never used as a matching criterion, CEFR_ORDER export confirmed to have exactly 1 new consumer with no other call site at risk). 2 Minor logged, not fixed: getRandomSavedExercise fetches the whole per-user collection and filters client-side (by design per spec, scales linearly - forward-looking note for a future composite-index pass), no try/catch in savedReadingExercises.ts (matches the existing vocabRecords.ts convention exactly, not a gap).

Task 2: complete (commit 5062a10..a2b770b, review clean/Approved — independently verified the implementer's own flagged deviation: the brief's literal Step 1 mock code (flat-object vi.mock) would have thrown at runtime since page.tsx also calls the real prioritizeUnusedWords from the same module; the vi.importActual+spread fix is correctly diagnosed and correctly applied, confirmed via the count:null->prioritize->slice ordering math and confirmed savedReadingExercises.ts has no top-level Firestore side effects making importActual safe). Corrected Task 3/4's own plan text (commit 850a10a) to show the real shipped mock pattern instead of the now-known-flawed flat-object one, applying the Task-1-incident lesson proactively before it could cause a stale re-dispatch. 1 Minor logged, not fixed: the importActual spread leaves saveReadingExercise/getRandomSavedExercise as real (Firestore-backed) implementations until Tasks 3-5 explicitly override them — already the documented plan for those tasks, just flagged for the next implementer to double check.

Task 3: complete (commit d27ec17..9c13318, review clean/Approved — fetchSavedExercise's 3-way branching (found/not-found-with-fallback/not-found-no-fallback), never-gated-by-min-words button state, vocabIds-never-a-matching-criterion, and error surfacing via generateError all independently re-verified against the diff). DONE_WITH_CONCERNS from the implementer: 1 test needed a manually-resolvable generateContent promise instead of mockResolvedValue, to fix a real (deterministic, not flaky) React-batching artifact where every mocked promise in the fetchSavedExercise->handleGenerate->generateContent chain resolved in one microtask burst, letting React flush past the intermediate "notice visible" state before screen.findByText could observe it. Reviewer independently traced the await chain and confirmed the diagnosis, confirmed the fix strengthens rather than weakens the test (now also asserts the session actually starts, not just that generateContent was called), and confirmed production page.tsx is byte-for-byte unmodified from the brief. 2 Minor logged, not fixed: no test for the getRandomSavedExercise-rejection->generateError path (out of the brief's specified 4 tests, not a compliance gap), fetchSavedExercise's "found" branch duplicates handleGenerate's session-reset boilerplate verbatim (plan-mandated, brief's own code is written this way).

Task 4: complete (commit fe6e9ff..986cffb, review clean/Approved — saveReadingExercise's 4-arg call order independently cross-checked against the real signature in savedReadingExercises.ts, "Lưu bài"/"Đã lưu" swap confirmed genuine DOM replacement not CSS hiding, VocabSuggestionsSection confirmed genuinely absent from DOM for reused sessions via queryByTestId, handleNewPassage/"Sinh bài mới" confirmed completely untouched by the diff with no drift into Task 5's territory). 2 Minor logged, not fixed: no direct test for the in-flight "saving" double-click guard itself (not in the brief's specified 3 tests), the save-error test asserts by text rather than by role="alert" so it wouldn't catch a dropped role attribute (matches the brief's own prescribed test code, not an implementer deviation).

Task 5: complete (commits 168c550..3474751..2454d2d, review found 1 Important — generateError had the exact same result-phase visibility gap the implementer had already self-caught and fixed for savedNotice, but hadn't extended the same audit to; fixed in commit 2454d2d with a 1-line mirror of the existing pattern, re-review independently traced every generateError-clearing call site to confirm the fix introduces no stale-error regression, confirmed the new test proves "visible on the result screen" not just "error state exists somewhere"). handleNewSession's 2-way branching, fetchSavedExercise reuse (not duplicated), and handleNewPassage's full removal all independently re-verified across both the original and re-review passes. DONE_WITH_CONCERNS from the implementer on Step 8 (manual Firestore-rules sanity check) — could not be performed in either implementer's environment (no browser/UI access, no firestore.rules file in-repo per this project's Console-managed rules setup) — still needs a manual check by the user or a browser-capable agent before the feature is considered fully verified end-to-end. 2 Minor logged, not fixed: "Sinh bài mới" has no disabled-while-in-flight guard or loading label unlike its setup-phase sibling buttons (a rapid double-click could fire 2 concurrent replay calls, no data corruption results since last-write-wins).

## All 5 tasks of Saved Reading Exercises (Đọc & gõ pilot) complete. Proceeding to final whole-branch review.

## Final whole-branch review (2f8bba0..2db43ed, 16 commits — spec+plan+5 tasks, reviewed on Opus): Ready to merge: With fixes.

Independently re-verified: typecheck clean, full suite 356/357 (1 pre-existing unrelated bloom.test.ts failure), production build clean (10 routes). Confirmed all 3 "already-resolved per-task" items genuinely held at the whole-feature level (vi.importActual mock pattern intact across Tasks 3-4, both savedNotice and generateError render in the result phase, records-fetched-once-on-mount reasoning verified structurally not hand-waved), confirmed the justSavedId-exclusion-never-fires limitation is still accurately true and untouched, confirmed word-priority has exactly one call site, confirmed no existing Firestore document shape changed (purely additive new collection).

4 Important findings, all with concrete reachable paths — the exact kind of cross-task integration bug a whole-branch review exists to catch (each individually correct in isolation, the interaction is what leaked):
- savedNotice never cleared after handleGenerate() succeeds -> stale "đang tạo bài mới bằng AI..." message leaks onto the finished result screen.
- saveError never cleared on session start -> a failed-save alert leaks into the NEXT session's result screen next to a fresh, never-clicked "Lưu bài" button.
- getAllUsedVocabIds awaited inside handleGenerate's main try -> a Firestore hiccup on the brand-new, not-yet-rules-verified reading_exercises collection hard-fails ALL AI generation, though word-priority is documented as a soft preference only.
- type: "bilingual" discriminant written on save but never enforced on read (matchesFilters, getAllUsedVocabIds) -> landmine for the next exercise type (Part5/6/7/Nghe) this schema is explicitly designed to grow into; a foreign-typed future document would either get handed to the Đọc & gõ typing session or crash getAllUsedVocabIds on a missing passage.vocabIds.

Fixed in one dispatched fix wave (commit 70584c5): savedNotice cleared in handleGenerate's finally (not the top, since fetchSavedExercise needs it visible during generation); saveError cleared at all 3 session-start sites (handleGenerate success, fetchSavedExercise's found branch, resetToSetup); getAllUsedVocabIds wrapped in .catch(() => new Set()) so a read failure degrades word-priority to a no-op instead of blocking generation; matchesFilters and getAllUsedVocabIds both gained a hardcoded (deliberately not parameterized) type !== "bilingual" guard. Added 1 integration test proving the saveError-leak fix specifically (generate -> save fails -> Sinh bài mới -> new session -> assert no stale alert), verified red-before/green-after.

Re-review (Opus) independently re-verified all 4 fixes at the exact required locations/ordering (savedNotice in finally not top; saveError's 3 sites enumerated with no 4th path missed; the .catch genuinely lets generation proceed with prioritizeUnusedWords degrading to a true no-op, not just relocating the error; the type guards sit ahead of the dereferences that would've thrown) and found no adverse interaction between the 4 fixes. Verdict: Ready to merge: Yes.

3 Minor findings from the re-review, not fixed: 3 of the 4 fixes (savedNotice-in-finally, getAllUsedVocabIds .catch, both type guards) have no DIRECT test coverage even though manually traced correct (only the saveError fix got a test); savedNotice can still survive handleGenerate's early-return guards (missing API key, no matching pool) since those return before the finally's setGenerating(true) — confirmed cosmetic-only, confined to the setup phase, cannot reach session/result screens; "Sinh bài mới" still has no in-flight double-click guard (already logged as an accepted Minor in Task 5's own review, unchanged).

**Open item for the human, not a code defect**: the Firestore security-rules manual sanity check (spec's own explicit ask — save via the real UI, confirm the write succeeds, confirm a subsequent "Lấy bài có sẵn" read succeeds) was never performed by any implementer or reviewer in this whole execution — no browser/UI access in any subagent's environment, and this repo has no firestore.rules file (Console-managed). The expectation that reading_exercises inherits the same per-owner rule as sibling vocab_records/topics is reasonable but genuinely unverified. This should be checked before considering the feature fully shipped end-to-end — Finding 3's fix (commit 70584c5) specifically softens the blast radius if this turns out to be wrong (a missing read rule now only breaks reuse/word-priority, not all of AI generation), but a manual check is still the right next step.

## Saved Reading Exercises (Đọc & gõ pilot, React web) — COMPLETE

All 5 tasks implemented and individually reviewed (Tasks 1/2/3/4 clean on first pass except Task 2's self-caught mock fix; Task 5 needed 1 review-driven fix), final whole-branch review found 4 Important cross-task integration bugs (all fixed in 1 dispatch, re-reviewed and confirmed correct with no new issues), several Minor findings logged throughout not fixed. 17 commits total (spec+plan+5 tasks+3 fix commits+ledger entries) on top of 2f8bba0. Independently re-verified at every stage: typecheck clean, full suite green apart from 1 known pre-existing unrelated CSS-lock failure, production build clean. Flutter port explicitly deferred to its own future spec per the original brainstorming decomposition (Option A). Manual Firestore-rules verification still needed from the user before considering this fully shipped end-to-end (see above).

## TOEIC Reading Part 5 (web, save/reuse from day one) — execution log

Task 1: complete (commits 0cfe9df..4606844, review clean/Approved — confirmed byte-for-byte match to the plan's prescribed code, the ex.type!==type guard confirmed unconditional and independent of filter-shape coincidences (satisfies "never return wrong-typed doc" for all inputs, not just the test's specific fixture), generic FiltersFor<T>/Extract<> machinery and its `as` casts confirmed sound via the compile-time+runtime dual guarantee, bilingual/page.tsx confirmed to have exactly the 2 call-site changes with no other line touched, bilingual/page.test.tsx confirmed same test count with only the 2 signature-sensitive assertions changed). 3 Minor logged, not fixed: the "never returns wrong type" test's premise slightly overstates what it proves (BilingualFilters/ToeicFilters share no fields so can't actually structurally collide, though the guard itself is still correct and unconditional), no negative-overlap test for part5 volumes (both-populated-disjoint branch), matchesBilingual/matchesToeic have slightly asymmetric parameter typing (harmless, matches brief).

Task 2: complete (commits c5a1bcd..489d089, review clean/Approved — all 8 ToeicContext values/labels and all 4 EconomyVolume values/labels verified verbatim against the brief including diacritics; VOLUME_PROMPT_HINTS independently cross-checked character-for-character against Flutter's real economy_volume.dart source, confirmed exact match not a paraphrase; correctly has no test file per the pure-data-constants convention). No findings.

Task 3: complete (commits ad25bc9..1f13f4d, review clean/Approved — prompt independently cross-checked line-by-line against Flutter's real part5_source.dart, confirmed verbatim on the 15-question/4-option/blank-marker/Vietnamese-script-explanation requirements and the empty-volumes-falls-back-to-all-hints behavior; parsePart5Set confirmed non-throwing on missing/malformed input with sane field defaults). 1 Minor logged, not fixed: cosmetic prompt wording diverges from Dart ("TOEIC difficulty levels" vs "Economy TOEIC difficulty volumes") with zero behavioral impact.

Task 4: complete (commits 88c545b..9da8dfd, review clean/Approved — session/result mode gating on correctIndex!==undefined (avoiding the falsy-0 trap) confirmed, disabled-click-does-not-fire-onSelect confirmed via a real behavioral test not just an attribute check, correct-always-highlighted/wrong-only-when-wrong confirmed mutually exclusive via the else-if construction, component confirmed fully generic with no Part5/6/7 leakage, confirmed stateless/pure). Reviewer's 1 ⚠️ item (CSS custom properties used by the new .mc-* rules actually defined, no class-name collision) independently resolved by the controller via grep: all referenced vars exist, no pre-existing .mc- classes conflict. 2 Minor logged, not fixed: aria-pressed applied even in disabled result mode (arguably wrong ARIA semantic for a disabled reveal state), className built via string concatenation rather than template literal (stylistic only).

Task 5: complete (commits d547e55..050458c, review clean/Approved — confirmed byte-for-byte match to the brief's page code, no word-count gate anywhere in the file, literal "part5" type argument used at both saveReadingExercise/getRandomSavedExercise call sites (not "bilingual"), handleNewSession's mode-replay branching correct with no dead MIN_VOCAB_WORDS fallback needed, Nộp bài submit-gating and score calculation both independently verified against test evidence, VocabSuggestionsSection gating confirmed, hub page confirmed to add exactly 1 new card/test without touching the existing Đọc & gõ one). Race-condition test-fix concern independently verified: confirmed same documented React-18-batching pattern already established in bilingual/page.test.tsx for the structurally identical notice-then-fallback scenario, confirmed the fix proves MORE not less than a naive version, confirmed production page.tsx character-for-character unmodified from the brief at that point. 2 Minor logged, not fixed: fetchSavedExercise's !handled branch is dead code inherited verbatim from the brief (user/settings already guaranteed loaded by the time it's reachable), 2 role="alert" nodes could theoretically coexist in an untested narrow edge case.

## All 5 tasks of TOEIC Reading Part 5 (web) complete. Proceeding to final whole-branch review.

## Final whole-branch review (c115136..d4ec530, 12 commits — spec+plan+5 tasks, reviewed on Opus): Ready to merge: With fixes.

Independently re-verified: typecheck clean, full suite 391/392 (1 pre-existing unrelated bloom.test.ts failure), production build clean. Confirmed all 3 "already-resolved per-task" items held at the whole-feature level (bilingual/page.tsx confirmed to have only the 2 signature-migration changes and nothing else, getRandomSavedExercise's type guard confirmed unconditional/precedes filter dispatch, part5/page.tsx confirmed byte-identical to the plan). Confirmed the sessionMode/justSavedId state machine traces correctly end-to-end against Task 1's new generic API, confirmed Part 5 has zero contact with getAllUsedVocabIds/prioritizeUnusedWords (the word-priority mechanism it has no business being part of), confirmed the empty-volumes-matches-anything rule engages correctly from UI state through to the Firestore matcher, confirmed McQuestionCard used identically at both session/result call sites with no Part5-specific leakage, confirmed Task 1's union is genuinely extensible for a future Part 6 with no further signature change needed.

3 Important findings, all real cross-task-integration/plan gaps no single task-scoped review could have caught alone:
- .mc-score (the result screen's score display) had no CSS rule anywhere in bloom.css -- rendered unstyled. Root cause: Task 4 reviewed CSS without the page, Task 5 reviewed the page without CSS -- a plan defect (the plan's own Task 4 CSS block omitted a class the plan's own Task 5 code used), faithfully implemented by both task implementers.
- No test coverage for a reused session's result screen (VocabSuggestionsSection/"Lưu bài" hidden, "Bài khác" replays fetchSavedExercise not AI) or for the save-error role="alert" path -- exactly the generate->save->reuse->result integration seam a whole-branch review exists to close.
- SavedReadingExercise's "part5" variant typed passage as unknown based on an incorrect belief that importing Part5Set into savedReadingExercises.ts would create an import cycle -- verified false (part5.ts only imports languages.ts/toeicFilters.ts, neither imports back), and the spec explicitly specified passage: Part5Set. An incorrect self-imposed constraint during Task 1's planning, not a deliberate tradeoff.

Fixed in one dispatched fix wave (commit 5624dd0): added a real .mc-score CSS rule (30px/800 weight/centered); added 3 tests for the reused-session path (VocabSuggestionsSection+Lưu bài genuine DOM absence via queryByTestId/queryByRole, "Bài khác" proven to call getRandomSavedExercise again and NOT generateContent) plus a save-error role="alert" test; imported the real Part5Set type into savedReadingExercises.ts, removed both now-unnecessary `as Part5Set` casts in part5/page.tsx, verified no import cycle by reading the actual chain (part5.ts -> languages.ts/toeicFilters.ts, neither imports back).

Re-review (Opus) independently re-verified all 3 fixes: the CSS rule is real and theme-valid (not a throwaway 1px rule); the reused-session tests genuinely await the result screen rendering before asserting absence (not vacuous) and the "Bài khác" test proves the correct branch fired by confirming generateContent was never called (which would have thrown on undefined text had the wrong branch run); the Part5Set typing is honestly satisfied by savedReadingExercises.test.ts's pre-existing FakePart5Set fixture (structurally identical, no as any escape hatch) and the no-cycle claim reconfirmed by reading part5.ts's actual imports. Confirmed the unknown->Part5Set tightening is purely compile-time with no runtime safety net lost (both before and after, a malformed stored doc throws at the identical point). Verdict: Ready to merge: Yes.

2 Minor findings from the re-review, not fixed: a stale comment in savedReadingExercises.test.ts still claims part5.ts "doesn't exist yet" (it does, and is now directly imported) -- misleading to a future reader though the fixture itself remains valid; the reused-session test fixtures use `as never` (an existing codebase convention for mocking generic functions) so they aren't compile-time-checked against the real Part5Set, meaning a future Part5Set shape change would break page.tsx but not flag these test fixtures as stale.

## TOEIC Reading Part 5 (web, save/reuse from day one) — COMPLETE

All 5 tasks implemented and individually reviewed clean on first pass (no fix cycles needed at task scope -- a first for this session's plans). Final whole-branch review found 3 Important cross-task-integration findings (all fixed in 1 dispatch, re-reviewed and confirmed correct with no new issues). 13 commits total (spec+plan+5 tasks+1 final-review-fix) on top of c115136. Independently re-verified at every stage: typecheck clean, full suite green apart from the 1 known pre-existing unrelated CSS-lock failure, production build clean. Part 6 and Part 7 remain for future plans per the original spec/scope decomposition -- Task 1's generic savedReadingExercises.ts API is confirmed to need no further signature change for them, and the process recommendation (extract a shared useSavedExerciseSession hook once a 3rd near-duplicate page appears) is logged for whoever writes Part 6's plan.

## Reading Hub / Setup Merge — execution log

Task 1: complete (commits 8a7caa1..cb82326, review clean/Approved — ToeicFilters/matchesToeic confirmed byte-for-byte match to brief and independently confirmed to mirror matchesBilingual's topic-overlap logic exactly; buildPart5Prompt's new signature and empty-topics-omits-clause behavior confirmed; ToeicContext/TOEIC_CONTEXTS/CONTEXT_LABELS confirmed deleted with zero remaining references anywhere in apps/web/src via independent grep; part5/page.tsx confirmed to use TopicFilterPopover with SimpleDropdown import fully removed; all 3 test files confirmed updated). No findings.

Task 2: complete (commits d334901..4b1bfbe, review clean/Approved — query-string encoding verified exact (topicIds/volumes/maxCefr omitted when empty/null, wordCount always present, action always set); min-5-word gate confirmed to apply only to Đọc & gõ's "Tạo bài luyện" via selectSessionWords(...).length >= MIN_VOCAB_WORDS, "Lấy bài có sẵn" unconditional for both modes, Part 5's "Tạo bài luyện" never gated; no default-selected mode confirmed; CSS addition confirmed non-colliding via grep; test file confirmed to cover all required scenarios; one disclosed justified fix to the brief's own test scaffolding, no scope deviation). No findings. A flaky unrelated vocab-bank/page.test.tsx timeout was observed once during a full-suite run and confirmed to be resource-contention flake (19/19 pass in isolation), not caused by this diff.

Task 3: complete (commits 62e262d..80ba674, review clean/Approved — all required dead imports/constants confirmed deleted via independent grep (TopicFilterPopover, SimpleDropdown/SimpleDropdownOption, CEFR_LEVELS, WORD_COUNT_OPTIONS, DEFAULT_WORD_COUNT, CEFR_DROPDOWN_OPTIONS, WORD_COUNT_DROPDOWN_OPTIONS); MIN_VOCAB_WORDS and exported ReadingSessionResult confirmed preserved; triggeredRef-guarded mount effect confirmed to redirect via router.replace on missing/invalid action and fire exactly once otherwise; both deliberate behavior changes (fetchSavedExercise's explicit generateError instead of silent no-op; handleNewSession's reused-branch no longer force-navigating) confirmed correctly wired, not just commented; Suspense confirmed wrapping the actual useSearchParams-calling component; npm run build independently re-run and confirmed /reading/bilingual is statically prerendered with no missing-Suspense-boundary error). No findings. Same flaky unrelated vocab-bank/page.test.tsx full-suite timeout observed again (19/19 in isolation) — confirmed pre-existing environmental flake, not caused by any task in this plan.

Task 4: complete (commits 48c1ad7..6f28724, review clean/Approved — implementer caught and fixed a genuine race condition in the plan's own brief code: the auto-trigger effect's literal gating (!user || !settings only) let handleGenerate() call buildPart5Prompt before the best-effort Promise.all([getVocabRecords, getTopics]) resolved, so topicIds never resolved to topic names in the AI prompt; fixed via a contextLoaded flag set in .finally() and added to the effect's guard/deps. Reviewer independently EMPIRICALLY verified the race by reverting to the brief's literal code and re-running the test suite -- 16/17 pass with the exact named test failing with the exact predicted error, then restored the fix and confirmed no diff. Confirmed no scope creep (only the contextLoaded gate touched, no Vietnamese text/CSS/param changes), confirmed .finally() correctly unblocks on fetch failure too, confirmed npm run build succeeds with /reading/part5 statically prerendered and no missing-Suspense-boundary error. 2 Minor logged, not fixed: contextLoaded gates action=existing too even though that path doesn't need resolved topic names (small unnecessary wait, not incorrect); an indefinite network stall on the best-effort fetch would leave the auto-trigger never firing for either action (same risk profile already accepted in Task 3's analogous records===null gate, not a new risk class).

## Final whole-branch review (8decfcc..d6d3aea, 10 commits — spec+plan+4 tasks, reviewed on Opus): Ready to merge: With fixes.

Independently re-verified: typecheck clean, full suite 405/406 (1 pre-existing unrelated bloom.test.ts failure), production build clean, all 3 pages statically prerendered with Suspense boundaries working correctly. Confirmed cross-task items no per-task review could see: query-param contract matches exactly in both directions for both modes (URLSearchParams percent-encoding of commas round-trips correctly); the hypothesized bilingual/part5 contextLoaded asymmetry does NOT exist as a bug (bilingual never needs resolved topic names, records!==null already implies topics populated -- Part5's gate really was the one that mattered); "always leaves visible feedback" invariant holds on all 4 fetchSavedExercise branches on both pages; Suspense pattern byte-identical on both pages, useSearchParams confirmed used nowhere else; zero remaining references anywhere to ToeicContext/TOEIC_CONTEXTS/CONTEXT_LABELS/appContext/CONTEXT_DROPDOWN_OPTIONS/resetToSetup; min-5-word bypass (1-4 words) degrades gracefully as documented.

2 Important findings, both genuine cross-task integration bugs invisible to per-task review:
- matchesToeic threw TypeError on pre-feature-shipped Part5 saved docs (old {appContext, volumes} shape, no topicIds field) -- newly reachable because Task 2 made topic-based navigation the primary flow.
- bilingual/page.tsx's handleGenerate had a silent `if (pool.length === 0) return;` with zero feedback -- newly reachable because Task 2/3 removed the setup-phase button-gating that used to prevent this path from ever firing with 0 words; a stale/hand-edited URL now hits a permanently blank loading screen.

Fixed in one dispatched fix wave (commit e5c58c9): matchesToeic guarded with `(exercise.generationFilters.topicIds ?? [])`; matchesBilingual correctly left untouched (topicIds has been a required field in every bilingual doc shape since day one, confirmed via git history, so no equivalent risk); handleGenerate's empty-pool branch now sets a Vietnamese generateError ("Không tìm thấy từ vựng nào khớp với bộ lọc đã chọn để tạo bài.") landing correctly in the existing loading-phase error UI with both Thử lại/Về trang chính buttons; Part5's page correctly left alone (no word-pool concept, no parallel bug). Added tests for both: a missing-topicIds-entirely fixture (not topicIds:[]) proving the crash is fixed, and a 0-word action=generate test asserting the exact error text plus both buttons.

Re-review (Opus) independently re-verified both fixes at the exact code paths, confirmed the test fixtures reproduce the original bugs via mutation testing (reverted fixes, confirmed 2 tests fail with the exact predicted symptoms, restored and reconfirmed green), confirmed matchesBilingual's guard-skip was correctly judged via git history not just trusted, confirmed no scope creep (4 files, +48/-2), confirmed npm run build still succeeds with all pages statically prerendered. Verdict: Ready to merge: Yes.

1 non-blocking coverage nicety noted, not fixed: no test for the empty-filter-against-missing-topicIds-doc case (provably safe by short-circuit, verified by reading the code).

## Reading Hub / Setup Merge — COMPLETE

All 4 tasks implemented and individually reviewed clean on first pass (Task 4 needed one implementer-caught, reviewer-empirically-verified fix to the plan's own brief code for a genuine mount-effect race condition; no other fix cycles needed at task scope). Final whole-branch review found 2 Important cross-task-integration findings (both fixed in 1 dispatch, re-reviewed and confirmed correct with no new issues). 12 commits total (spec+plan+4 tasks+1 final-review-fix) on top of 8decfcc. Independently re-verified at every stage: typecheck clean, full suite green apart from the 1 known pre-existing unrelated CSS-lock failure (plus one confirmed-flaky, confirmed-pre-existing vocab-bank timeout under full-suite load, unrelated to this feature), production build clean with all 3 reading pages statically prerendered. Part 6/7/Nghe are explicitly deferred to their own future spec/plan cycles, adopting this same hub pattern from the start per the spec's own "Deferred" section.

## TOEIC Reading Part 6 (web) — execution log

Task 1: complete (commits a73a13d..1c65d45, review clean/Approved — buildPart6Prompt/parsePart6Set confirmed byte-for-byte match to brief; prompt wording independently cross-checked word-for-word against Flutter's real part6_source.dart, the empty-topics-omits-register-clause deviation confirmed deliberate (mirrors part5.ts's identical pattern); parsePart6Set's question-count filter confirmed applied AFTER defaulting malformed fields, not before, via direct trace of the loop; test suite confirmed to exercise both filter-ordering cases precisely (4 malformed-but-present survives, fewer-than-4 dropped)). No findings.

Task 2: complete (commits d7fd829..abb545f, review clean/Approved — "part6" union member confirmed byte-for-byte match to brief, Part6Set confirmed imported from Task 1's real module not a duck-typed stand-in, no existing function body touched (matchesToeic/saveReadingExercise/getRandomSavedExercise/getAllUsedVocabIds/FiltersFor/PassageFor all byte-identical), union semicolon placement confirmed syntactically correct; the critical cross-type test (does not return a part5 exercise when requesting part6, despite byte-identical ToeicFilters) confirmed to be a genuine regression guard by tracing getRandomSavedExercise's ex.type!==type guard runs unconditionally before any filter dispatch; test fixtures confirmed to avoid the earlier Part5 addition's stale-comment/type-drift Minor by typing directly against the real Part6Set import). No findings.

Task 3: complete (commits 0517651..fd62354, review clean/Approved — Mode type/buildQuery/navigate/gating-condition/volume-chip-guard/new-card all confirmed byte-for-byte match to brief; navigate's 3-way ternary routing traced for all 3 modes with no misrouting; gating condition's mode!=="bilingual" simplification confirmed logically equivalent to mode==="part5"||mode==="part6" by hand-tracing all 3 mode values; existing Đọc & gõ/Part 5 cards confirmed completely untouched; no new query param introduced). No findings.

Task 4: complete (commits 0ebc4dc..4d150cf, review clean/Approved — page/test/CSS confirmed byte-for-byte match to brief; flat-index formula passageIndex*4+questionIndex confirmed consistently applied via a single flatIndex() helper at every read/write site (handleSelectAnswer, both array-sizing sites in handleGenerate and fetchSavedExercise, session-phase selected prop, result-phase selected/correctCount); contextLoaded gate confirmed correctly ported from Part 5 (set via .finally(), included in both guard and deps); parsePart6Set's outer passages.length===0 check confirmed correct given the module's own internal 4-questions-per-passage filter; "Chỗ trống (N)" labeling confirmed to reset per-passage (qi+1, not a running total) in both session and result JSX; literal "part6" confirmed at both save/fetch call sites, no part5 copy-paste; VocabSuggestionsSection text confirmed to join all 3 passages not just the first; CSS classes confirmed non-colliding via grep; npm run build independently re-run confirming /reading/part6 statically prerendered with no missing-Suspense-boundary error). No findings.

## All 4 tasks of TOEIC Reading Part 6 (web) complete. Proceeding to final whole-branch review.

## Final whole-branch review (3753233..86492a9, 9 commits — plan+4 tasks, reviewed on Opus): Ready to merge: With fixes.

Independently re-verified: typecheck clean, full suite 445/446 (1 pre-existing unrelated bloom.test.ts failure), production build clean, /reading/part6 statically prerendered. Confirmed cross-task items no per-task review could see: query-param contract round-trips correctly for both actions with/without topics/volumes (including percent-encoded commas and special characters); cross-type save/reuse correctness proven via 400 randomized draws against real Part5Set/Part6Set-shaped Firestore mocks (part6 never returns part5-shaped data or vice versa, type guard runs before any filter dispatch); "always leaves visible feedback" invariant holds across 9 traced failure scenarios; Suspense pattern has zero drift from Part5/Đọc & gõ; part5/part6 page duplication confirmed to be the spec's own deliberate stated choice, not a defect, with a note to consider extracting a shared hook at Part 7's spec stage (a third copy); hub card grid confirmed to already have a 3rd auto-fill track reserved (zero layout change to the 2 existing cards).

1 Important finding: no automated test ever exercised a multi-passage (3-passage/12-blank) Part6Set, so flatIndex's cross-passage arithmetic was completely unguarded -- every existing fixture had exactly 1 passage, which degenerates almost any indexing formula to the same result, meaning an off-by-one or wrong-multiplier bug would pass the whole suite green.

Fixed in one dispatched fix wave (commit 9a97c09, test-only, no production code changed): added THREE_PASSAGE_SET (genuine 3-passage/12-blank fixture, all 48 options unique) plus 4 new tests covering full 3-passage rendering, cross-passage independent slot mapping, submit-gating across all 12 slots (11 spread across all 3 passages, not clustered), and scoring across all 3 passages (8/12 from a deliberate correct/incorrect mix). Re-review (Opus) independently verified via actual mutation testing: temporarily broke flatIndex to passageIndex+questionIndex and to passageIndex*questionIndex, reran, confirmed the new tests fail at the exact predicted lines with the exact predicted aria-pressed symptom while all 18 pre-existing tests still passed under the broken formula (proving the gap was real), then reverted and reconfirmed 22/22 clean with an empty git diff on page.tsx. Confirmed scoring arithmetic correct by hand-checking all 12 clicks against their correctIndex. Confirmed test isolation via 3 shuffled runs all giving 22/22. Verdict: Ready to merge: Yes.

4 Minor findings logged, not fixed (consistent with prior features' precedent of accepting known small trade-offs): notice/error paragraphs can visually stack on the result screen in a rare fallback-after-fallback sequence (cosmetic only, same pattern already accepted in the hub-merge feature); part5/page.tsx and part6/page.tsx share ~170 near-identical lines with no shared hook extracted -- explicitly the spec's own stated design choice ("structurally identical to part5/page.tsx"), not a defect, flagged as a good extraction point once Part 7 makes it a third copy; QUESTIONS_PER_PASSAGE (page.tsx) duplicates BLANKS_PER_PASSAGE (part6.ts, module-private) rather than sharing one constant; a stale pre-existing untracked file test-results-before.txt sits at the repo root, unrelated to this feature. One re-review process note (not a code defect): the fix wave's own report undercounted the full suite (53/420) due to a transient Windows fork-worker flake silently dropping 7 files from that one run -- both the controller's and the re-reviewer's independent re-runs confirmed the true clean count is 60 files/450 tests.

## TOEIC Reading Part 6 (web) — COMPLETE

All 4 tasks implemented and individually reviewed clean on first pass. Final whole-branch review found 1 Important cross-task-integration finding (test coverage gap on multi-passage flat-indexing, fixed in 1 dispatch and re-verified via actual mutation testing, not just re-reading). 11 commits total (plan+4 tasks+1 final-review-fix, plus their ledger-log commits) on top of 3753233. Independently re-verified at every stage: typecheck clean, full suite green apart from the 1 known pre-existing unrelated CSS-lock failure, production build clean with /reading/part6 statically prerendered alongside /reading/bilingual and /reading/part5. Part 7 and Nghe remain for future spec/plan cycles, adopting this same hub-integrated pattern from the start per this feature's own spec's "Deferred" section -- and Part 7 is the natural point to consider extracting a shared session hook from the now-3-times-duplicated page pattern (Đọc & gõ is structurally different enough not to count as a 4th copy, but part5/page.tsx and part6/page.tsx are near-identical).

## TOEIC Reading Part 7 (web) — execution log

Task 1: complete (commits 62e686b..cdb2e53, review clean/Approved — buildPart7Prompt/parsePart7Set/hasValidPart7Shape confirmed byte-for-byte match to brief; prompt text independently cross-checked word-for-word against Flutter's real part7_source.dart; hasValidPart7Shape confirmed a line-for-line port of Flutter's _hasValidShape with boundary cases verified (accepts 3/4, rejects 2/5 for single groups, rejects non-5 for double group); parsePart7Set confirmed to never throw and do no shape filtering of its own, correctly deferring to hasValidPart7Shape; test suite confirmed to exercise real boundary cases not just happy-path). No findings. Confirmed pre-existing unrelated vocab-bank/page.test.tsx timeout via the repo's own test-results-before.txt baseline predating this task.

Task 2: complete (commits a4b4855..4804d03, review clean/Approved — "part7" union member confirmed byte-for-byte match to brief, Part7Set confirmed imported from Task 1's real module; no existing function body touched; union semicolon placement confirmed syntactically correct; the critical 3-way discrimination test (part7 vs part5 vs part6, all sharing identical ToeicFilters shape) confirmed to be a genuine regression guard by tracing getRandomSavedExercise's ex.type!==type guard runs unconditionally before any filter dispatch, independent of how many types share a filter shape). No findings.

Task 3: complete (commits 4b02283..2e59ad8, review clean/Approved — Mode type/buildQuery/navigate/volume-chip-guard/new-card all confirmed byte-for-byte match to brief; navigate's nested 4-way ternary confirmed correctly routes all 4 modes to distinct paths; volume-chip guard's mode!=="bilingual"&&mode!==null simplification confirmed to correctly preserve the null-hides-filter behavior (the && mode!==null clause was NOT forgotten); existing 3 cards confirmed untouched). No findings. Full-suite run showed transient timeouts on vocab-bank and (for the first time) one of Part6's own multi-passage tests under Windows fork-pool load -- both independently re-confirmed passing 100% in isolation (Part6: 22/22, vocab-bank: 19/19), consistent with growing suite size increasing resource contention, not a regression from this diff (which touches only reading/page.tsx and its own test file).

Task 4: complete (commits af52bc7..66bd226, review clean/Approved — page/test confirmed byte-for-byte match to brief; flatIndex's running-sum formula hand-traced against the (3,4,5) fixture confirming correct offsets (0, 3, 7) with no off-by-one/multiplier/+1 bugs, and confirmed the shipped test suite genuinely exercises cross-group indices (group0 vs group2), not just group 0 -- the exact test a broken formula would fail; totalQuestions confirmed a true sum used consistently in both array-sizing sites; hasValidPart7Shape confirmed called immediately after parsePart7Set and throwing the exact Vietnamese string matching Part5/6's own; question numbering confirmed to reset per group; double-document heading confirmed derived from documents.length===2 (data-driven, not position-assumed); literal "part7" confirmed at both save/fetch call sites; VocabSuggestionsSection text confirmed to flatten every document of every group; no new CSS added, confirmed reuse of Part6's existing classes; npm run build independently re-run confirming /reading/part7 statically prerendered with no missing-Suspense-boundary error). No findings.

## All 4 tasks of TOEIC Reading Part 7 (web) complete. Proceeding to final whole-branch review.

## Final whole-branch review (d78c3e4..c3c69e5, 9 commits — plan+4 tasks, reviewed on Opus): Ready to merge: Yes.

No Critical or Important findings. Independently re-verified: typecheck clean, full suite 498/499 (1 pre-existing unrelated bloom.test.ts failure, no worker flakes this run), production build clean, /reading/part7 statically prerendered. Confirmed cross-task items no per-task review could see: end-to-end query-param contract verified empirically for all 4 modes x both actions including no cross-mode filter leakage (bilingual's wordCount/maxCefr never leaks to part7, part5's volumes selection correctly carries to part7); three-way cross-type save/reuse (part5/part6/part7 sharing identical ToeicFilters) verified end-to-end with real getRandomSavedExercise against a mocked 3-doc Firestore response, confirming Part7Set never gets rendered from Part5Set/Part6Set-shaped data; "always leaves visible feedback" invariant confirmed to hold even for hasValidPart7Shape failing on a Bài khác-triggered regenerate (not just initial mount), not swallowed; Suspense pattern confirmed zero drift across all 4 reading pages; shape-validation design intent (parsePart7Set non-throwing, hasValidPart7Shape as the page's own separate throw-trigger) confirmed followed consistently via full-tree grep showing exactly one call site, never called on saved-exercise read-back; hub card grid confirmed to have no hardcoded card-count assumption anywhere; part5/part6/part7 duplication confirmed to be exactly the spec's own predicted, deliberate trade-off with no new urgency to extract a shared hook (would reconsider if Nghe becomes a 4th near-copy).

4 Minor findings logged, not fixed (3 are pre-existing patterns already carried by Part 5/6, not new to Part 7): the 4th hub card orphans onto its own grid row (cosmetic, no functional impact, no hardcoded assumptions broken); a malformed saved Part7 doc would surface a raw untranslated English TypeError message (caught and shown via generateError, so the "always visible feedback" invariant still holds -- same exposure Part5/6 already have); an empty passageGroups:[] on a saved doc would vacuously enable Nộp bài for a 0/0 result (unreachable given hasValidPart7Shape gates everything that gets saved, same as Part5/6's equivalent gap); hasValidPart7Shape doesn't validate per-question option counts, matching Flutter's own _hasValidShape which also doesn't check this -- a faithful port limitation, not a regression.

## TOEIC Reading Part 7 (web) — COMPLETE

All 4 tasks implemented and individually reviewed clean on first pass, no fix cycles needed at task scope. Final whole-branch review found zero Critical/Important findings -- clean "Ready to merge: Yes" with only 4 Minor observations, 3 of which are pre-existing patterns shared with Part 5/6 rather than anything Part 7 introduced. 9 commits total (plan+4 tasks+their ledger entries) on top of d78c3e4. Independently re-verified at every stage: typecheck clean, full suite green apart from the 1 known pre-existing unrelated CSS-lock failure, production build clean with all 4 reading pages (/reading/bilingual, /reading/part5, /reading/part6, /reading/part7) statically prerendered. This closes out the full TOEIC Reading Parts 5/6/7 initiative on web (Nghe/Listening remains for its own future spec/plan cycle, adopting this same hub-integrated pattern from the start).

## Nghe chép (Dictation, web) — execution log

Task 1: complete (commits 015421e..99de18e, review clean/Approved — synthesizeSpeech confirmed byte-for-byte match to brief with exact signature (request {text, language:"vi"|"en"} -> Promise<{audioBase64}>), confirmed calls Cloud Function by the exact string "synthesizeSpeech" (no typo that would silently fail at runtime); toAudioDataUrl confirmed builds exactly data:audio/wav;base64,... matching the confirmed Piper Content-Type; scope confirmed exactly 2 new files). No findings.

Task 2: complete (commits 43ab494..cc6e896, review clean/Approved — dictation.ts confirmed byte-for-byte match to brief; every claimed "exact port" independently cross-checked against the real Flutter source (dictation_source.dart, select_dictation_blanks_use_case.dart, dictation_practice_provider.dart): buildDictationPrompt word-for-word except deliberately omitted level/context clauses (matches this feature's own no-topic-filter scope decision, not a defect); selectDictationBlanks/easy/medium confirmed line-for-line identical including the 30-attempt retry cap, hand-traced to prove no infinite loop possible; normalizeForComparison confirmed to strip edge punctuation per-word (not whole-string) matching Dart's exact order; charAccuracy confirmed divides by target.length not typed.length; computeDictationScore/sm2QualityFromScore confirmed exact clamp order and all SM-2 boundary values including the deliberately-missing "1" tier). 2 Minor findings logged, not fixed: prioritizeDueWords uses <= where Flutter uses strict < for the due-time comparison (unreachable in practice, millisecond-exact tie); parseDictationItem's vocabWords.map(String) silently coerces non-strings where Dart's List<String>.from would throw (a reasonable robustness improvement, not a bug).

Task 3: complete (commits 630162d..537bc22, review clean/Approved — savedListeningExercises.ts confirmed byte-for-byte match to brief; confirmed no audio field anywhere in the saved document shape via grep; saveListeningExercise confirmed to write its own id field in the document body matching the established savedReadingExercises.ts pattern; getRandomSavedListeningExercise confirmed to filter targetLanguage via the Firestore query and difficulty via exact in-memory equality (not overlap), correctly excluding excludeId; scope confirmed exactly 2 new files). No findings.

Task 4: complete (commits d4b2cdd..37b39c0, review clean/Approved — useDictationAudio.ts confirmed byte-for-byte match to brief; all state-transition rules traced through the actual code and confirmed exact (play()'s fullClipUrlRef-gated fetch correctly handles the seek-before-play interaction so a first play after a seek still doesn't increment replayCount; seekTo() confirmed to always re-fetch fresh, never cache; the no-penalty-on-first-seek asymmetry confirmed exact); error handling confirmed to never corrupt hasPlayedOnce/replayCount/seekCount/seekPenaltyTotal state on a rejected synthesizeSpeech call; setSpeed() confirmed pure client-side with no backend call; the jsdom "no workaround needed" claim empirically verified by running the isolated test file and confirming the brief's own defensive guard correctly no-ops jsdom's unimplemented HTMLMediaElement.play()). No findings.

Task 5: complete (commits 361e3ca..ae78fda, review clean/Approved — ClozeInput/DiffText/tests/CSS confirmed byte-for-byte match to brief; ClozeResult.tsx has one deliberate 1-line deviation (adds .toLowerCase() to the hint text) that the implementer made and the reviewer independently VERIFIED was necessary, not implementer error -- reverting to the plan's literal brief code and re-running the brief's own test causes it to fail, since the fixture sentence "Apple is red" makes targetTextForBlank return "Apple" (capital A) while the brief's own test used a case-sensitive /đúng: apple/ regex; a genuine inconsistency in the plan itself, correctly caught and fixed. Word-index bookkeeping for both cloze components hand-traced correct across all test cases; DiffText confirmed no out-of-bounds access; all CSS classes confirmed matching between TSX and bloom.css with no typos; scope confirmed exactly 6 new files + 1 CSS edit). No blocking findings.

Task 6: complete (commits c12be66..ccd5b86, review clean/Approved — page.tsx confirmed byte-for-byte match to brief; language gate confirmed to check before any word-eligibility computation and render zero buttons (not disabled state); eligible-word count confirmed to filter specifically on record.targetLanguage==="english" via getVocabRecords returning all-language records client-side; "Lấy bài có sẵn" confirmed structurally identical to the established reading-hub ungated pattern; default difficulty="hard" and query-string shape confirmed to exactly match what Task 7's destination page expects). page.test.tsx has one necessary 3-line deviation from the brief: the brief's own "prompts sign-in" test never configured a useSettingsContext mock, but the component calls that hook unconditionally (before the !user check, since hooks can't be conditional) -- an unconfigured vi.fn() mock returns undefined, crashing the destructure. Implementer added a default beforeEach mock; reviewer independently verified by reverting to the brief's literal code and confirming it throws. Checked Task 7's own brief for the same gap -- not present, since its sign-in test explicitly sets both useAuthUser and useSettingsContext together, not relying on a beforeEach default. No blocking findings.

Task 7: complete (commits 35942b5..4ab4428, fix e36b351, review clean/Approved after 1 fix cycle — /listening/dictation/page.tsx confirmed byte-for-byte match to brief; word selection, wordMap/parseDictationItem correctness, blank recomputation for both generated and reused sessions, the submit gate, SM-2 update correctness, and save/reuse state hiding all confirmed on the first pass). First-pass review found 1 Critical cross-task bug invisible to any single task's own tests: `useDictationAudio(item?.target ?? "")` lives on a persistent page-component instance, so starting a second session in the same visit (e.g. "Câu khác") inherited the first session's `hasPlayedOnce`/`replayCount`/`seekCount`/`seekPenaltyTotal`/cached audio clip — silently bypassing the listen-before-submit gate, replaying the wrong sentence's audio, and corrupting the score fed into SM-2. Neither Task 4's hook tests (never re-rendered with a changed sentence) nor Task 7's own tests (never exercised a second session per render) could have caught this. Fix (e36b351): added a `useRef` tracking the previous `sentence` plus a `useEffect` keyed on `[sentence]` that resets all six state pieces and pauses in-flight audio on a genuine sentence change, explicitly skipping the reset on initial mount. Fix re-review independently verified rather than trusted: hand-traced the mount-vs-change distinction (`useRef(sentence)` seeds the ref with the first render's value, so the first effect run always sees "no change"); confirmed all six state pieces are reset, not a subset; confirmed in-flight audio is paused; confirmed the new test uses `rerender` on the same hook instance (not a fresh `renderHook`, which would trivially pass without exercising the reset path) and asserts `synthesizeSpeech` is called with the NEW sentence on the next `play()` (proving the cache was actually invalidated, not just the counters); empirically confirmed the test is load-bearing by temporarily short-circuiting the reset effect and re-running it (failed exactly as predicted), then restoring and re-confirming a clean suite; confirmed `play()`/`setSpeed()`/`seekTo()` bodies are byte-identical to the pre-fix version (purely additive fix, no rewrite); confirmed the consuming page file has zero diff in the fix commit (fix lives entirely in the hook, no `key`-prop workaround). Independently re-ran: hook tests 11/11, page tests 17/17 (unchanged, no regression), full suite 590 passed/1 pre-existing unrelated bloom.test.ts failure, tsc --noEmit clean. Verdict: Ready to merge: Yes.

## Final Whole-Branch Review

**Commits reviewed:** 872c021..f40e7c8 (17 commits — plan+7 tasks+their ledger entries), reviewed on Opus.
**Status:** Ready to merge: With fixes (1 Critical, 3 Important).

Independently re-verified: full suite 590/1 pre-existing unrelated bloom.test.ts failure, tsc --noEmit clean, production build clean with /listening and /listening/dictation both statically prerendered. Scoring-formula port audit cross-checked every formula (charAccuracy, blockAccuracy, normalizeForComparison, seekPenaltyFraction, computeDictationScore, sm2QualityFromScore, selectDictationBlanks, buildDictationPrompt) line-by-line against the real Flutter source — no simplification found. Save/reuse confirmed to never persist audio and to always recompute blanks fresh from the current difficulty. SM-2 update confirmed best-effort per-word with the same displayed/graded score. Suspense pattern confirmed structurally identical to the reading pages. All 8 error paths across both difficulty modes and both session origins traced and confirmed to leave visible feedback — no silent-freeze path found.

**Critical:** the e36b351 reset-on-sentence-change fix from Task 7 was keyed on the sentence *string*, not session identity — a reused session that re-picks the SAME saved exercise (e.g. only one match exists, so "Câu khác" on a reused session returns the identical document) never triggers the reset, since `item.target` is byte-identical. Playback state (hasPlayedOnce/replayCount/seekCount/seekPenaltyTotal/cached clip) leaks exactly as Task 7's original finding described, just for a narrower trigger the fix's own test didn't cover.

**Important (3):** (1) the seek slider called `audio.seekTo` directly from `onChange`, so a single drag across many words fired one `synthesizeSpeech` call and one seek penalty per intermediate tick — Flutter's reference only seeks on `onChangeEnd`. (2) the `targetLanguage !== "english"` gate existed only on the hub, never on `/listening/dictation` itself — reachable directly via bookmark/back-button/live Settings change in another tab. (3) local `records` state was never refreshed after an SM-2 write, so a second same-visit session via "Câu khác" could re-select an already-reviewed word and recompute `computeSm2` from a stale repetitions:0 base, silently failing to advance its schedule on the repeat review — `practice/page.tsx` already solves this exact problem and was the pattern to mirror.

**Minor (8, not fixed, logged for awareness):** TTS errors surface in raw English, not Vietnamese, contradicting spec §Error handling (the plan's own test was already internally inconsistent about this); ClozeResult lowercases the correct-answer hint, diverging from Flutter's original-casing display (a reasoned Task 5 deviation, not new); the hub has no named "🎤 Nghe chép" card per spec, just a bare picker; the seek slider is uncontrolled and doesn't reset its thumb between sessions, and Flutter's while-dragging "Từ N/M" indicator wasn't ported; `speed` is not reset by the sentence-change effect (arguably correct — preserves user preference); `blankAnswers.every(...)` is vacuously true on an empty array (unreachable in practice); no "Về trang chính" escape on the session screen if TTS keeps failing (consistent with the reading session screens); "Câu khác" has no in-flight indicator/disable (byte-identical pre-existing pattern in `reading/part5/page.tsx`, not a regression).

**Fix applied (commit ca70e98):** all 4 blocking findings fixed in one consolidated commit. (1) added a `sessionKey` argument to `useDictationAudio`, bumped by `startSession` on every call (both generated and reused paths), reset effect now fires on sentence-OR-sessionKey change. (2) seek slider's `onChange` now only updates local preview state; the actual `seekTo` call moved to `onMouseUp`/`onTouchEnd`/`onKeyUp` (covering drag, touch, and keyboard release), slider disabled while `audio.isLoading`. (3) added the same language gate to `DictationPageContent`, checked before the auto-trigger effect can invoke `handleGenerate`/`fetchSavedExercise`. (4) merged the just-written SM-2 fields into local `records` state after each successful Firestore write, mirroring `practice/page.tsx`'s established pattern exactly.

**Fix re-review (independently verified, not trusted):** all 4 fixes confirmed via revert-and-observe-failure experiments — reverting each fix in turn made its own new test fail with exactly the predicted symptom, then restored to a clean, zero-diff state. Confirmed the sessionKey bump happens on both `handleGenerate` and `fetchSavedExercise` (not just one, which would have silently reintroduced the exact reused-same-item leak this fix targets). Confirmed the seek release handlers read the live DOM value at release, not a stale closure. Confirmed the language gate blocks at the effect level (traced with instrumented logging, not just the JSX render) — `generateContent`/`synthesizeSpeech` genuinely never fire when gated. Confirmed the SM-2 merge uses the actually-written fields (not a re-derived value) and is independent per-word (one word's Firestore failure doesn't block the other's merge); verified the merged math against `sm2.ts` by hand (repetitions:0→quality 5 gives interval:1/repetitions:1; repetitions:1→quality 5 gives interval:6/repetitions:2 — matches the test's asserted values). Full suite 596 passed/1 pre-existing unrelated bloom.test.ts failure, tsc --noEmit clean. Verdict: Ready to merge: Yes.

**New Minor (from fix re-review, not fixed):** the language-gate test (`page.test.tsx`) is racy — its `screen.findByText` assertion resolves on the gate message's unconditional first synchronous render, before the async `getVocabRecords`-then-effect-refire chain would have had a chance to fire `generateContent` if the effect-level guard were absent. Production code is confirmed correct by direct trace; the test itself just doesn't provide real regression protection for the effect-level half of the fix. Suggested follow-up: add `await waitFor(() => expect(getVocabRecords).toHaveBeenCalled())` before the `not.toHaveBeenCalled()` assertion.

## Nghe chép (Dictation, web) — COMPLETE

All 7 tasks implemented and reviewed clean (1 task-level fix cycle: Task 7's audio-state-leak). Final whole-branch review found 1 Critical + 3 Important cross-task findings invisible to any single task's own review — all 4 fixed in one consolidated commit (ca70e98) and independently re-verified via revert-and-observe experiments, each confirmed to close its exact failure scenario. 19 commits total (spec+plan+7 tasks+their ledger entries+final review fix+this closeout) on top of 872c021. This closes out the Nghe chép (Dictation) initiative on web — English-only scope (forced by `synthesizeSpeech`'s `"vi"|"en"` backend constraint), save/reuse supported despite Flutter's version having none (audio is cheap to regenerate from saved text, never persisted). Nghe hiểu (Listening Comprehension) remains deferred to its own future spec/plan cycle.

---

# LexiCore — Nghe chép Audio Playback Improvements

**BASE commit (plan start):** 872c021
**Spec:** docs/superpowers/specs/2026-08-24-nghe-chep-audio-playback-improvements-design.md (commit 0f9f5d3)
**Plan file:** docs/superpowers/plans/2026-08-24-nghe-chep-audio-playback-improvements.md (commit 1f75f4c)

## Status

Task 1: complete (commit c6a2944, review clean/Approved — play()'s 3-branch restructuring traced by hand for all paths (cached-clip, in-flight-prefetch-await, fresh-fetch), confirmed prefetch never sets hasPlayedOnce in either .then()/.catch(), confirmed reset effect clears prefetchPromiseRef (not just fullClipUrlRef) preventing a stale cross-session promise leak, confirmed effect declaration order (reset-effect-then-prefetch-effect) prevents a new prefetch being clobbered by a stale reset. Implementer found and fixed 5 additional pre-existing tests beyond the brief's named 2 — a genuine unavoidable consequence of prefetch now calling synthesizeSpeech earlier, not scope creep; reviewer independently read each of the 5 fixes and confirmed none weakened its original assertion's intent. "Reuses in-flight prefetch" test confirmed non-vacuous via a manually-controlled never-resolving mock proving no duplicate call fires before the await settles). No findings.

Task 2: complete (commit 16b95e9, review clean/Approved — timeupdate listener confirmed attached exactly once (same lazy-creation guard as the <audio> element), confirmed reads sentenceRef.current (not a stale closure) so a "Câu khác" sentence swap with a different word count is picked up correctly rather than staying stuck on the old count; NaN/Infinity duration guard traced to prevent setEstimatedWordIndex from ever firing before metadata loads; clamp formula confirmed to bound output to [0, totalWords-1] including 1-word and currentTime-overshoot edge cases; all 3 required baseWordIndexRef/estimatedWordIndex call sites confirmed present (play's cached-clip branch, play's fetched branch, seekTo's success path); reset effect confirmed to zero both on session change. Reviewer empirically mutation-tested twice (hardcoded-0 clamp, disconnected-Audio-instance spy) confirming the relevant tests genuinely fail with the predicted symptom, then restored both to a clean, zero-diff state). No findings.

Task 3: complete (commit 6622419, review clean/Approved — page.tsx confirmed verbatim match to brief (isDraggingSeekRef, sync effect, all 5 slider handlers); ref-ordering confirmed isDraggingSeekRef set false as the FIRST statement in the release handlers, before seekTo fires, so no window where sync stays blocked after a seek completes. Implementer flagged a test-only race (the sync effect's flush could land after a subsequent synchronous test interaction, stomping a fresh value) fixed via an added waitFor in the test — reviewer did not accept this at face value: independently reproduced the race by removing the waitFor (failed 4/4 with the exact predicted symptom, restored and passed 4/4), then reasoned through real-browser event-loop/scheduler timing to confirm it's genuinely unreachable outside the test harness's synchronous zero-delay event dispatch (human/programmatic DOM events are separated by tens of ms at minimum; React's passive-effect flush completes in microseconds, and the effect is self-healing via continuous timeupdate events regardless). Both new tests confirmed non-vacuous by deliberately reverting the drag guard and confirming the predicted test failure. Step 2 (fixing 3 pre-existing tests) independently confirmed a genuine no-op — Task 1 had already fixed all 3 via an equivalent pattern). No findings.

Task 4: complete (commit aa08d14, review clean/Approved — SPEEDS constant confirmed fully removed with zero remaining references, replaced with named MIN_SPEED/MAX_SPEED/SPEED_STEP constants (no inlined magic numbers); old 3-button JSX confirmed fully removed not left dead; useDictationAudio.ts confirmed untouched (empty diff); onChange confirmed to call audio.setSpeed directly per-tick with no release-gating, confirmed meaningful since useDictationAudio is the real unmocked hook in these tests; new test confirmed non-vacuous (would fail if release-gating were mistakenly copied from the seek slider); aria-label confirmed Vietnamese; CSS classes confirmed non-colliding via grep, single definition/single use each. npm run build independently re-run confirming /listening/dictation still statically prerenders). No findings.

## Final Whole-Branch Review

**Commits reviewed:** c22dc4b..da18ff3 (10 commits — spec+plan+4 tasks+their ledger entries), reviewed on Opus.
**Status:** Ready to merge: With fixes (3 Important, 4 Minor).

Independently re-verified: full suite 607/1 pre-existing unrelated bloom.test.ts failure, tsc --noEmit clean, production build clean with /listening/dictation statically prerendered. Confirmed the invariant "no scoring/backend changes" held across the whole branch (diff touches exactly 6 files: 2 source, 2 test, bloom.css, docs). Confirmed prefetch never touches the <audio> element (timeupdate listener only attached inside playUrl, which prefetch never calls). Confirmed sentenceRef staleness fix from Task 2 still correct after Tasks 3/4. Confirmed no dead code (SPEEDS fully gone, old button JSX removed, no orphaned CSS). Cross-session reset audit ran on all 4 new state pieces the plan added (baseWordIndexRef, estimatedWordIndex, prefetchPromiseRef, isDraggingSeekRef) — the specific class of bug this review was asked to hunt for, given it was the Critical finding in the original Nghe chép plan.

**Important (3), all found via the cross-session audit and confirmed empirically, not speculatively:**
1. Stale `speed` value baked into `playUrl` via `useCallback`'s dep array (`[sentence, hasPlayedOnce]` excludes `speed`) — first play, every replay, and every seek silently played at 1x regardless of the slider's real value/label. Predates this branch (same defect existed in the old 3-button UI) but Task 4's entire deliverable was making speed a first-class live control, so this is exactly the gap Task 4's own reviewer couldn't see (verified setSpeed is called per-tick, not that the value survives into playback).
2. The seek slider's drag-guard (`isDraggingSeekRef`) covered mouse/touch but not keyboard — a keyboard user scrubbing with arrow keys could have the live-playhead sync effect stomp their in-progress value before release, landing on the wrong word AND charging the wrong `seekPenaltyFraction` (a genuine, if narrow, violation of the "estimatedWordIndex never feeds scoring" invariant).
3. A late-resolving prefetch from a DISCARDED session (e.g. user seeks — which doesn't force the prefetch to settle, unlike play() — then starts a new session before the old prefetch resolves) had no guard against clobbering the new session's cached clip; the reset effect only stopped the new session's play() from awaiting the stale promise, not the stale promise's own callback from writing into the shared ref afterward. Latent (unreachable via the ordinary Play path) but a genuine variant of the exact state-leak class that was the original plan's Critical finding — the design spec's own reasoning for why this needed no handling was factually wrong and has been corrected.

**Minor (4, 2 fixed alongside the Important fixes, 2 logged only):** a related stale-rejection variant of finding 3 (wasted duplicate fetch, closed by the same guard); `isDraggingSeekRef` never reset on a new session, freezing live-tracking forever if a drag gesture is abandoned without a release event (fixed); the design spec's incorrect line 33 claim (corrected); a test using persistent `mockRejectedValue` instead of `mockRejectedValueOnce` twice (cosmetic, not fixed).

**Fix applied (commit 6d0f0f3):** all 3 Important findings plus the 2 related Minors fixed in one consolidated commit. (1) added `speedRef` mirroring the existing `sentenceRef` pattern, `playUrl` now reads `speedRef.current`. (2) added `onKeyDown` to the seek slider's guard-arming handlers alongside `onMouseDown`/`onTouchStart`. (3) added a `cancelled` flag to the prefetch effect, set in its cleanup function, guarding both `.then()`/`.catch()` bodies. (Minor) `isDraggingSeekRef` reset added to `startSession`; design spec's incorrect paragraph corrected.

**Fix re-review (independently verified via revert-and-observe, not trusted):** all 3 fixes confirmed by reverting each in turn and observing its new test fail with exactly the predicted symptom, then restoring to a byte-exact clean state. Finding 1's test specifically checks the real `<audio>` element's `playbackRate` (not just the reported `speed` state, which was never wrong — this is the detail that would have missed the original bug). Finding 2's test genuinely fires a competing `timeupdate` mid-keyboard-gesture. Finding 3's two tests cover both the success and rejection stale-callback branches. Full suite 613 passed/1 pre-existing unrelated bloom.test.ts failure, tsc --noEmit clean. Verdict: Ready to merge: Yes.

## Nghe chép Audio Playback Improvements — COMPLETE

All 4 tasks implemented and reviewed clean (no task-level fix cycles needed — Tasks 1-4 all passed on first review, including two tasks where the reviewer empirically mutation-tested the implementation and a race-condition claim before approving). Final whole-branch review found 3 Important cross-task findings invisible to any single task's own review — all fixed in one consolidated commit (6d0f0f3) and independently re-verified via revert-and-observe experiments, each confirmed to close its exact failure scenario. 12 commits total (spec+plan+4 tasks+their ledger entries+final review fix+this closeout) on top of c22dc4b. This closes out the audio playback improvements initiative for Nghe chép on web: prefetch now genuinely speeds up the first Play click (not just replays), the seek slider shows a live time-proportional estimated playhead that correctly tracks mouse/touch/keyboard interaction without fighting the user, and speed control is a continuous 0.5x-2x slider with correctly-applied real-time playback.

---

# LexiCore — Nghe hiểu (Listening Comprehension) on Web

**BASE commit (plan start):** c22dc4b
**Spec:** docs/superpowers/specs/2026-08-24-nghe-hieu-listening-comprehension-design.md (commit 5cf5dad, corrected ad1b7bc)
**Plan file:** docs/superpowers/plans/2026-08-24-nghe-hieu-listening-comprehension.md (commit ad1b7bc, Task 1 corrected 473ddc7)

**Pre-flight correction (before Task 1 dispatch):** discovered while about to dispatch that services/tts-stt/voices/ does not exist in the repo — Piper model files are downloaded fresh at Docker build time via curl, never git-committed. The original Task 1 draft would have had the implementer download 3 .onnx files locally and git-add them, and would have required real voice files for its own new tests to pass (no test in this service has ever exercised real Piper synthesis before). Fixed before dispatch: Task 1 now extends the Dockerfile's existing curl block instead, and its tests mock PiperVoice entirely, matching this codebase's established boundary-mocking convention.

## Status

Task 1: complete (commit ae097c1, review clean/Approved — 4-voice registry confirmed byte-for-byte match to brief; _load_voice fallback logic confirmed exact (unsupported voice on single-voice language falls back silently, on multi-voice language raises); Dockerfile's 3 new curl pairs confirmed correctly placed and URL-exact; confirmed zero binary files/voices directory committed anywhere. Implementer found a genuinely pre-existing test file (tests/test_synthesize.py) the brief's own research had missed, with one stale assertion broken by the new 3-arg synthesize() signature — reviewer independently confirmed via git log this file predates the task, confirmed it covers different boundary/cases than the new tests (no coverage lost), and empirically reverted the fix to confirm it fails with exactly the predicted stale-arity symptom before restoring. Mock genuineness confirmed for the 4-distinct-voice-paths test — real production path-resolution code runs under the mock, a real aliasing bug would genuinely fail it). No findings.

Task 2: complete (commit 19ca383, review clean/Approved — SynthesizeSpeechRequest/VALID_VOICES/validation confirmed byte-for-byte match to brief; cloudRunClient.ts's voice threading confirmed to produce a genuinely absent JSON key when omitted (not null/"undefined"), verified via a live `JSON.stringify` check; grep confirmed no other apps/web caller of synthesizeSpeech needs updating. Implementer independently found and fixed a pre-existing test broken by the handler now always forwarding a 4th argument (even undefined) to synthesizeViaCloudRun — reviewer did not take this at face value: empirically confirmed via a throwaway vitest file that toHaveBeenCalledWith genuinely distinguishes a 3-arg call from a 4-arg call with a trailing explicit undefined, confirmed the fix adds a real non-vacuous 4th-arg expectation matching the brief's own new test pattern, and checked 2 other files with similar-shaped assertions for the same latent bug class (both confirmed unaffected, correct reasoning given for each)). No findings.

Task 3: complete (commit c98f54c, review clean/Approved — all 8 AppContext values/labels/emoji independently cross-checked value-by-value against app_context.dart, confirmed exact match; test coverage confirmed to check every one of the 8 contexts has a non-empty label AND emoji, not just object existence). No findings.

Task 4: complete (commit fdc40a4, review clean/Approved — buildListeningPassagePrompt independently line-diffed against listening_passage_source.dart's real _buildPrompt, confirmed word-for-word except the one documented gender addition; ListeningKind/ListeningTurn/ListeningQuestion confirmed matching listening_passage.dart's shape; scoreComprehension confirmed logically equivalent to Flutter's correctCount getter, correctly expressed as a ratio. speakerGenders first-seen-wins loop hand-traced with a gender-flip scenario, confirmed first value sticks. assignVoices hand-traced for all 5 cases (male-female, female-male, male-male, female-female, solo) confirmed always 2 distinct slots for same-gender pairs. Tests confirmed non-vacuous on the trickiest cases including a genuine null-vs-correctIndex-0 off-by-one-style test). No findings. Minor doc-only note carried over: brief's "Consumes" list mentions targetWords reuse that this task's code never actually needs (harmless, targetWords is genuinely used in Task 5 instead).

Task 5: complete (commits fdc40a4..983c9b4, fix 63147b3, review clean/Approved after 1 fix cycle — the most complex task in the plan (per-turn prefetch maps, auto-advance recursion with play-token supersession, two-level global word-index scheme). First-pass review found 1 Critical bug via empirical probing, not just inspection: currentTurnIndexRef was synced via a delayed useEffect instead of synchronous assignment at each mutation site (the one outlier vs. baseGlobalWordIndexRef/playTokenRef's established synchronous pattern in this same file), so two mutator calls in one React batch (e.g. nextTurn();nextTurn(); or nextTurn();play();) had the second call act on a stale pre-update turn index — reproduced with a throwaway probe showing both a stuck-at-1-instead-of-2 case and a wrong-turn-audio case. All other things the review brief asked to trace independently (N-turn cancelled-guard sharing one closure across the whole prefetch loop, speedRef read fresh through every playback path including auto-advance, 3 play-token race scenarios, global word-index math against a concrete 3/5/2-word example, the speakerFor hygiene wiring, hardcoded language:"en") confirmed correct on inspection and empirical testing. Fix (63147b3): removed the delayed effect, added synchronous currentTurnIndexRef assignments at all 6 setCurrentTurnIndex call sites, added 2 regression tests chaining calls within one act() block. Fix re-review independently confirmed all 6 sites fixed (none skipped), the delayed effect fully removed, both new tests genuinely non-vacuous (single act() block, not two), and empirically reverted the fix to confirm both tests fail with the predicted symptom — the re-reviewer's own revert additionally surfaced that the pre-fix bug was actually WORSE than first characterized: play()'s own setCurrentTurnIndex(0) call (using the stale ref) could win a state-update race against nextTurn()'s setCurrentTurnIndex(1) in the same batch, snapping the index backward, not just leaving a stale ref. Full suite 11/11 clean, tsc clean. Verdict: Ready to merge: Yes.

Task 6: complete (commits 8823ee9..3999156, fix deeb573, review clean/Approved after 1 fix cycle — production code (generic FiltersFor<T>/ItemFor<T> mirroring savedReadingExercises.ts's real pattern exactly, unconditional type-guard before filter dispatch, exact context+level equality matching for comprehension) confirmed correct throughout by hand-trace and mutation testing. speakerGenders persistence bug (caught during this plan's own pre-dispatch self-review) confirmed genuinely fixed — required non-optional field on ComprehensionItem, matching listeningPassage.ts's real Speaker/SpeakerGender types. All 4 call sites confirmed accounted for via full-tree grep. First-pass review found 1 Important + 1 Minor via mutation testing (not just inspection): the "never returns a dictation doc" cross-type test was vacuous (silently inherited an empty mock from the prior test, passed even with the type guard deleted); the comprehension save test only checked the returned id's type, never that speakerGenders actually reached the persisted document. Fix (deeb573, test-only, confirmed zero production-code changes): rewrote the cross-type test to seed a real dictation-shaped doc with filters that would trivially match if the guard were absent, and added a genuine setDoc assertion checking speakerGenders. Fix re-review independently reproduced the guard-deleted failure and restored a byte-identical production file, confirmed the save assertion checks the real persisted shape). No findings. Verdict: Ready to merge: Yes.

Task 7: complete (commit 1109fc4, review clean/Approved — page.tsx/page.test.tsx confirmed byte-identical to brief; multi-card pattern independently confirmed to genuinely match reading/page.tsx's real established structure (mode defaults null, conditional filter rows, .reading-hub-cards CSS reused unmodified), not a superficial reimplementation; dictation's 2-word vocab gate confirmed to not leak into comprehension's unconditional generate button; query-string shapes hand-traced for both cards including the level dropdown's UI-default (null/"Tất cả") vs. buildQuery's independent "b1" URL fallback; language gate confirmed to still block both cards entirely before the grid renders; card-switch state persistence confirmed intentionally consistent with reading hub's own identical (no-reset) behavior, not a regression; CSS "no changes needed" claim independently verified against the actual auto-fill/minmax grid rule). No findings.

Task 8: complete (commit 8337137, review clean/Approved — the test file flagged during planning as unverified-by-execution turned out correct as written, no fixes needed. Cross-task integration seams verified hard, as this is the final task before whole-branch review: hub buildQuery/page useSearchParams parsing confirmed consistent both directions (same context/level default fallbacks on both sides); useComprehensionAudio wiring confirmed correct argument order/types against Task 5's real signature, assignVoices confirmed called once per session not per render; the reused-session speakerGenders fix from this plan's own pre-dispatch self-review confirmed genuinely landed — fetchSavedExercise bypasses parseListeningPassage entirely and restores speakerGenders directly from the saved doc, not silently defaulting to {}; global word-count math confirmed identical between the page's inline split and dictation.ts's real targetWords helper, keeping the seek slider's max in sync with the hook's actual reachable range; handleSubmit confirmed to call the real scoreComprehension (not a reimplementation), hand-traced for a 2/3 partial-credit case; save shape confirmed to include all 4 ComprehensionItem fields including speakerGenders. Every error path (missing API key, empty AI response, save failure, fetch-saved failure) traced and confirmed to always leave visible role="alert" feedback, never a blank/frozen screen. npm run build independently re-run confirming all 16 routes including /listening/comprehension statically prerender clean). No findings.

## All 8 tasks of Nghe hiểu complete. Proceeding to final whole-branch review.

## Final Whole-Branch Review

**Commits reviewed:** c22dc4b..e381248 (33 commits, of which 20 belong to this plan — spec+plan+8 tasks+their ledger entries; the remainder are the prior Nghe chép audio-improvements plan, already separately reviewed and closed out at d0f5a60), reviewed on Opus.
**Status:** Ready to merge: With fixes (3 Important, 8 Minor).

Independently re-verified: full suite 657/1 pre-existing unrelated bloom.test.ts failure, tsc clean across apps/web AND functions, production build clean with /listening, /listening/dictation, /listening/comprehension all statically prerendered, functions suite 74/74, services/tts-stt pytest 21/21. Cross-session reset on "Bài khác" empirically re-verified end-to-end through Task 8's real page code (not just Task 5's isolated hook review) — every piece of state genuinely resets, the cancelled-guard genuinely holds against a late-resolving stale prefetch. Deploy-order safety verified both directions (client sending voice against the not-yet-redeployed backend, and vice versa) — confirmed safe either way via direct trace of the pre-Task-2 Cloud Function/TTS code. Confirmed zero SM-2/replayCount/seekPenalty/listen-gate references anywhere in the feature's own files via grep. No dead code/TODOs found.

**Important (3), all found and confirmed via empirical probing, not just inspection:**
1. The seek playhead's timeupdate formula used the full turn's word count even after a seek loaded only a remainder clip — baseGlobalWordIndexRef was written at 6 sites but never actually read, so the offset it existed to carry was silently discarded. Empirically probed: seeking to global word 25 of a 3x10-word passage made the first post-seek timeupdate report word 20, then sweep 20 to 29 across a 5-word clip — visibly snapping backwards then racing ahead for the entire remainder. Direct deviation from the design spec's explicit requirement to mirror useDictationAudio's base-relative formula.
2. The global seek slider had no drag-guard at all (spec explicitly required porting Nghe chép's pattern; the task brief silently dropped it, which is why Task 8's own narrower reviewer never caught it — only visible against the spec, not the brief). Every onChange tick fired a real seekToGlobalWord/TTS synthesis call; while playing, the live-bound value fought the user's drag.
3. The hub's "Tất cả" (All levels) label for comprehension always sent level=b1 in the query string (unlike reading's hub, which omits an unset filter), making any saved exercise at a level other than B1 permanently unreachable via "Lấy bài có sẵn" with no indication to the user why.

**Minor (8):** wrong page name ("Nghe chép") in the comprehension page's own language-gate message; hub gate message named only one of its two features; a vacuous stale-prefetch regression test (expect(true).toBe(true)); no test coverage for estimatedGlobalWordIndex under a real timeupdate event (the direct cause Important #1 survived 8 task reviews); no page-level "Bài khác" test, and the reused-session test never confirmed persisted speakerGenders actually drove voice selection (the exact regression that field exists to prevent); handleSubmit never stopped playback, leaving audio auto-advancing into the result phase; a write-only dead ref (subsumed by fixing #1); a voice:undefined-to-null Firebase-callable-encoding edge case that would reject once the new Cloud Function deploys (not reachable today, but the type contract permitted what the runtime would reject).

**Fix applied (commit a92f681):** all 3 Important + 6 related Minor findings fixed in one consolidated commit. (1) added localBaseWordIndexRef tracking the currently-loaded clip's own local offset, deleted the dead baseGlobalWordIndexRef. (2) ported dictation's full seekPreviewIndex/isDraggingSeekRef pattern, added a new isSeeking flag on the hook wired to the slider's disabled. (3) hub now omits level when unset (matching reading's pattern); ComprehensionFilters.level widened to CefrLevel or null; matchesComprehension treats null as "match any level" on the lookup side only; the generate path keeps its concrete "b1" fallback unchanged. Plus: corrected both gate messages, rewrote the stale-prefetch test to genuinely assert on audio src, added real-timeupdate coverage including a seek case, added a Bài khác flow test and a reused-speakerGenders-drives-voice-assignment test, added audio.stop() to handleSubmit.

**Fix re-review (independently verified via revert-and-observe on every fix, not trusted):** Finding 1 — reverted the local-base read to a hardcoded 0, confirmed the new test failed with the exact predicted wrong value (7 instead of 9), restored clean. Finding 2 — reverted onChange to call seekToGlobalWord directly, confirmed the drag-tick test failed with 3 real synthesis calls during drag instead of 0, restored clean. Finding 3 — confirmed handleSaveExercise never persists a null level (traced the actual variable used, not the raw URL param); confirmed the generate path is unaffected; reverted matchesComprehension to strict equality, confirmed the "matches at any level" test failed, restored clean. All 6 Minor fixes independently confirmed non-vacuous via the same revert technique (stale-prefetch test caught a reverted cancelled-guard; handleSubmit's stop() caught its own removal). Full suite 668/1 pre-existing unrelated failure, tsc clean, build clean with all 3 routes prerendering. Verdict: Ready to merge: Yes.

## Nghe hiểu (Listening Comprehension) — COMPLETE

All 8 tasks implemented and reviewed clean (2 task-level fix cycles: Task 5's currentTurnIndexRef staleness, Task 6's vacuous cross-type test — both found via empirical mutation testing, not inspection). Final whole-branch review found 3 Important + 8 Minor cross-task findings invisible to any single task's own review — all fixed in one consolidated commit (a92f681) and independently re-verified via revert-and-observe experiments, each confirmed to close its exact failure scenario. Plan required one real pre-dispatch correction (Task 1's original draft would have git-committed voice model binaries and required real Piper models for its own tests — corrected to extend the existing Dockerfile curl-download mechanism and mock PiperVoice entirely, before any task was dispatched) plus one design bug caught during the plan's own self-review (speakerGenders would not have survived save/reuse without deliberately persisting it, unlike the ephemeral voice-slot choice which correctly never persists). 20 commits total (spec+plan+8 tasks+their ledger entries+2 task-fix cycles+final review fix+this closeout) on top of c22dc4b. This closes out the Nghe hiểu initiative on web and, with it, the full "Nghe" (Listening) feature area: Nghe chép (Dictation) and Nghe hiểu (Listening Comprehension) both now live on web with save/reuse support Flutter never had, a shared 4-voice-capable TTS backend (2 voices actively used by Nghe chép today, all 4 by Nghe hiểu once services/tts-stt/ and functions/ are redeployed), and battle-tested audio-playback patterns (prefetch, cancelled-guards, drag-guarded seek sliders, ref-based "always current" values for lazily-attached listeners) proven across both features. **Deploy note carried forward:** this feature requires two manual deploys before it's live in production — gcloud run deploy for services/tts-stt/ (the 4-voice registry) and firebase deploy --only functions for functions/ (the voice parameter contract) — neither was part of any task in this plan, per the plan's own Global Constraints.

**2026-08-25 update:** the one remaining unverified step from Task 1 is now closed — the user listened to the norman voice sample (rhasspy.github.io/piper-samples) and confirmed it sounds male and acceptable. male2 in the Dockerfile stays en_US-norman-medium as originally chosen; no fallback substitution needed. Only the two manual deploys above remain before this feature is live in production.

---

# LexiCore — Tổng quan (Dashboard) on Web

**BASE commit (plan start):** 374f5c8
**Spec:** docs/superpowers/specs/2026-08-25-dashboard-tong-quan-design.md (commit 318e164)
**Plan file:** docs/superpowers/plans/2026-08-25-dashboard-tong-quan.md (commit 374f5c8)

## Status

Task 1: complete (commit f141850, fix/clarification 80c71ec, review clean/Approved after 1 review-override cycle — implementation confirmed byte-for-byte match to brief; mastered threshold and CEFR breakdown confirmed faithful ports of stats_service.dart's real logic. First-pass reviewer flagged the isDue comparison (nextReviewAt <= now) as a Critical divergence from Flutter's stats_service.dart (which uses strict isBefore, i.e. <), recommending a change to match Flutter exactly. Controller investigated and overrode this recommendation: apps/web/src/lib/practiceSession.ts's own already-shipped isDue (the function /practice actually uses to select due words for a session) uses the identical <=, not <, and changing learningStats.ts to strict < would make /dashboard's due-count disagree with what /practice actually selects as due for a word landing exactly on `now` -- worse than an edge-case Flutter-parity gap, since both live in the same app. Dispatched a documentation-only fix (comment + 1 locking test) instead of the reviewer's suggested behavior change. Re-review independently verified the override (traced isDue's real call site through selectSessionWords into practice/page.tsx's actual session-selection path, confirmed it's load-bearing not dead code) and found EVEN STRONGER concrete evidence than the controller's own reasoning: this plan's own Task 3 spec has /dashboard's CTA literally promise "Ôn N từ ngay" then link to /practice?action=start's auto-start, which calls the exact same selectSessionWords -- a disagreement between the two isDue functions would make the CTA's promised count mismatch the actual auto-started session on the very next screen, a concrete bug not a hypothetical. Re-reviewer independently agreed with the override on the merits, not by deference. Logged Minor, not fixed: isDue is now duplicated verbatim across 2 files linked only by a comment, a DRY nit worth a future shared-helper extraction, not a correctness issue).

## Task 2: dailyActivity.ts — complete

Implemented `apps/web/src/lib/dailyActivity.ts` + test (commit `0b500cd`), ported from `stats_service.dart`'s `recordPracticeSession`. Mirrors `settings.ts`'s single-doc-per-user Firestore pattern (`users/{uid}/stats/activity`).

Implementer (sonnet) flagged and self-fixed a timezone bug in the brief's own planned test fixture: the same-day-repeat-call test used UTC (`Z`-suffixed) timestamps (10:00Z/18:00Z) that cross local midnight in this repo's Asia/Saigon (UTC+7) dev/CI environment, making the two calls land on different local calendar days and incorrectly fail. Fixed by dropping the `Z` suffix (local-time literals) — implementation file left untouched, only the test fixture changed.

Reviewer (sonnet) independently re-verified this diagnosis rather than trusting the report: confirmed the environment's actual timezone (Asia/Saigon, UTC+7) via `Intl.DateTimeFormat`, confirmed the original `Z` timestamps really do cross local midnight, confirmed the fix's corrected timestamps land on the same local day, and re-ran the test to verify. Also did a full line-by-line comparison of `recordDailyActivity` against the real `stats_service.dart` source (same-day/consecutive-day/gap/prune cases) — all match exactly.

Spec: ✅. Code quality: Approved. 3 Minor findings logged, none blocking: (1) `getDailyActivity` returns the shared `DEFAULT_ACTIVITY` object by reference on missing-doc, same pre-existing pattern as `settings.ts`'s `DEFAULT_SETTINGS` — not a regression; (2) TS omits a `?? 1` defensive fallback Dart has for its same-day branch, unreachable in both since Firestore writes `currentStreak`/`lastPracticedDate` atomically together (unlike Dart's two separate SharedPreferences writes); (3) no `firestore.rules` coverage for the new path, equally true of the existing `settings.ts` path already.

Task 2: complete (commits f09643f..0b500cd, review clean).

## Task 3: /dashboard page — complete

Implemented `apps/web/src/app/(app)/dashboard/page.tsx` + test + `bloom.css` additions (commit `281d970`), consuming Tasks 1-2. Streak banner (2 states), 2 stat cards, CTA (aria-hidden arrow), 6-level CEFR breakdown, hand-rolled 7-day CSS bar chart. No new charting dependency.

Review (sonnet): spec ✅, code quality — 1 Important + 3 Minor findings. Important: `getVocabRecords` failure was silently swallowed to an empty array with no user-facing indication (inherited from the brief's own sample code, which diverged from the brief's own instruction to mirror `practice/page.tsx`'s `loadError` convention) — a failed vocab fetch would render as "user has 0 words" with no alert. Minors: chart recomputed `lastNDays`/`Math.max` every iteration instead of once; redundant `role="link"` on a Next.js `<Link>`; streak error message interpolated a raw JS `Error.message` into an otherwise-Vietnamese string.

Dispatched a fix (commit `05831eb`) addressing all 4 findings: added an independent `recordsError` state + Vietnamese `role="alert"` for the stats section (verified genuinely independent from `activityError` — separate `.then/.catch` chains, not `Promise.all`), hoisted the chart's per-render computations, removed the redundant role, and made the streak error message plain Vietnamese with no diagnostic interpolation. Added a test for the new error state.

Re-review (sonnet): Approved — all 4 findings verified resolved by reading the actual code (not just the report), new test asserts the two error states stay independent, 8/8 dashboard tests + tsc clean.

Task 3: complete (commits d6eb3ab..05831eb, review clean after 1 fix round).

## Task 4: /practice?action=start auto-trigger + daily-activity record — complete

Modified `apps/web/src/app/(app)/practice/page.tsx` (commit `7db1686`): added the page's first-ever `useSearchParams()`/`<Suspense>` wrapper (verified byte-for-byte pattern parity with `listening/dictation/page.tsx`), an `action=start` auto-trigger calling `selectSessionWords` with `count: null` (uncapped) so the auto-started session size matches the Dashboard CTA's promised due-word count, and a `recordDailyActivity(user.uid, sessionResults.length)` call added inside the existing SM-2-batch-write effect (guarded by the pre-existing `sm2WrittenRef`, fire-and-forget with `.catch(console.error)`).

Review (sonnet): independently confirmed `selectSessionWords` semantics genuinely bypass the picker's default cap, confirmed the Suspense wrapper matches an existing page's pattern exactly, confirmed the daily-activity call is single-fire/non-blocking inside the correct existing effect (not a new racing effect), confirmed all 11 pre-existing tests were left assertion-unchanged (only additive), confirmed the new tests' flip-click + "Chưa hiểu"/"Đã hiểu" labels are real and correct against `FlashcardCard.tsx`. 15/15 tests pass, tsc clean, build clean.

Spec: ✅. Code quality: Approved. Zero findings (Critical/Important/Minor) — first task this plan with a clean first-pass review, no fix round needed.

Task 4: complete (commits 841f41a..7db1686, review clean, no fix round).

## Task 5: 6-page daily-activity integration — complete

Added `recordDailyActivity` calls to the 6 remaining result pages (commit `aaba323`): `reading/bilingual`, `reading/part5`, `reading/part6`, `reading/part7` (each via a new `useEffect`+guard-ref pair, since none had an existing "runs once on result phase" effect), `listening/dictation` and `listening/comprehension` (inline in their existing `handleSubmit`, at the point `phase` becomes `"result"`). Completes the Global Constraint that streak/weekly-log scope matches Flutter exactly across all 7 result screens (Ôn tập was Task 4).

Review (sonnet) checked all 6 files individually rather than sampling, and found an Important bug specific to the 4 reading pages: each has a `handleNewSession()` ("Làm bài mới" button) that transitions the SAME component instance back into a new session in place, without remounting — but the new guard ref was never reset there, so `recordDailyActivity` only fired for the FIRST session completed per page load; every subsequent in-place session silently dropped its word count from the weekly log. The 2 listening pages don't have this bug (their calls are inline in `handleSubmit`, re-fired fresh on every submission).

Controller independently verified before dispatching a fix (mirroring the Task 1/Task 3 override-investigation pattern): confirmed `handleNewSession()` in `reading/part5/page.tsx` really doesn't reset the ref, then confirmed the established correct convention already exists in this exact codebase — `practice/page.tsx`'s own `sm2WrittenRef` guard is explicitly reset (`sm2WrittenRef.current = false;`) inside `handleStart()` at line 122. This proved the finding was a genuine implementation gap (the brief's snippet just omitted the reset), not a deliberate design choice, so a fix was dispatched rather than escalated.

Fix (commit `6723583`): added the equivalent one-line reset at the start of `handleNewSession()` in all 4 reading pages, plus a test per file asserting a SECOND `recordDailyActivity` call fires after a second in-place session.

Re-review (sonnet): Approved — went further than reading the diff: temporarily reverted the fix in 2 of the 4 files and reran the new tests to confirm they genuinely fail without the fix (not just re-asserting the first call), then restored the files and confirmed a clean `git status`. 90/90 pass, tsc clean.

Task 5: complete (commits f54a9da..6723583, review clean after 1 fix round; 1 Important finding independently verified and fixed, not just accepted on the reviewer's word).

## Final whole-branch review — complete

Dispatched on opus (most capable available model, per skill guidance for final reviews), covering the full branch diff (16 commits, `8835ed4..5f6b2cf` — MERGE_BASE = the commit right before the design spec was first committed).

Independently re-verified rather than trusting the ledger: ran the full test suite (697/697), `tsc --noEmit`, and `npm run build` itself; wrote and ran its own temporary probe test against `practice/page.tsx` to confirm a second in-place session really does fire a second `recordDailyActivity` call; temporarily reverted the Task-5 ref-reset fix in `part6/page.tsx` a SECOND time (independently of the Task-5 re-reviewer) to re-confirm the fix is load-bearing. Traced `isDue` end-to-end across `learningStats.ts` → `practiceSession.ts` → `/practice?action=start`'s auto-trigger to confirm the Task 1 override genuinely makes the dashboard's promised due-count match what the CTA actually starts.

**Verdict: Ready to ship, no fix round required.** Zero Critical findings, zero correctness defects, zero spec gaps. Both prior override/fix decisions (Task 1's `isDue` override, Task 5's ref-reset fix) held up under fresh independent scrutiny.

2 Important findings — both test-coverage gaps on code that already behaves correctly, not live bugs — were folded in before closing (commit `ee7b746`): (1) `practice/page.tsx` had no automated test for the same "second in-place session" scenario that already needed a real fix in the 4 reading pages, even though its own reset happens to be safe today (piggybacking on `sm2WrittenRef`, not a daily-activity-owned ref) — added the equivalent test; (2) the dashboard's 7-day CSS chart (the branch's only new UI mechanism) had zero test coverage — added tests for 7-column count, zero-fill on missing days, chronological order, and today's visual distinction.

8 Minor findings logged, not actioned (none blocking, several are pre-existing patterns or faithful Flutter-parity choices, not regressions):
- Dashboard subtitle claims "real-time" updates but the page only fetches on mount (no `onSnapshot`) — copy overclaim, `dashboard/page.tsx:77`.
- `dateKey()` duplicated verbatim between `dailyActivity.ts` (writer) and `dashboard/page.tsx` (chart reader) — must stay in sync or the chart silently reads nothing; should be exported from `dailyActivity.ts` instead.
- The 4 reading pages' effect+ref block for `recordDailyActivity` is identical across all 4 files — a shared hook (`useRecordActivityOnResult`) would collapse the duplication and the Task-5 bug class structurally.
- `recordDailyActivity`'s Firestore read-modify-write is not transactional/merged — two near-simultaneous calls (two tabs, or two exercises finished within ~300ms) can clobber each other. Within the declared best-effort constraint and matches Flutter's own non-atomic SharedPreferences pair, so not a spec violation; cheap hardening available later (`{merge:true}` + `increment()`, or `runTransaction`) if it ever matters.
- Streak has no staleness/expiry check — a 10-day-old streak displays unchanged until the next session resets it. Faithful port of Flutter's own behavior (no staleness check there either), flagged only because the web dashboard is a prominent top-level sidebar destination vs. Flutter's buried "Tiến độ học tập" card — a deliberate future divergence, not a bug, if ever wanted.
- 🔥/❄️ banner emoji lack `aria-hidden` (the CTA's `→` correctly has it) — screen readers would announce "fire"/"snowflake".
- No `firestore.rules` file exists in this repo to verify the new `users/{uid}/stats` path against (Console-managed rules) — the README's documented recursive `users/{userId}/{document=**}` rule almost certainly already covers it, but this plan (unlike prior plans in this repo) had no explicit rules-verification step, and a permission-denied write would be invisible by design (swallowed by the mandated best-effort `.catch(console.error)`) — **recommend a manual post-deploy check: finish any exercise, reload `/dashboard`, confirm the streak and today's bar actually moved.**
- Minor CSS eyeball-worthy item: `.dash-chart-value`'s `top: -18px` positioning at a 1000.000000e+00ight bar — likely fine given the card's padding, but worth a visual check at a real max value.

# Tổng quan (Dashboard) on Web: PLAN COMPLETE

All 5 tasks implemented, individually reviewed (1 fix round each on Tasks 1, 3, 5; Task 2 and Task 4 passed clean on first review), and the whole branch passed final review with one small test-coverage fix round. 18 commits total (`318e164..ee7b746`). Nothing pushed to `origin/master` yet.

# LexiCore — Quét từ vựng (Word Radar) on Web

## Task 1: HighlightedText shared component — complete

Implemented `apps/web/src/components/shared/HighlightedText.tsx` + test (commit `34f0309`), a direct port of Flutter's `word_radar_screen.dart`'s `_HighlightedText` matching algorithm (earliest-occurrence-wins, no length tie-break) — verified line-by-line against the real Dart source by the reviewer, including tracing a case where a shorter, later-in-candidate-list word still wins because its occurrence starts earlier in the text. Two variants: `interactive` (clickable, opens a popover reusing the existing `PronunciationButton`) and `static` (plain `<mark>`, no click handler — used by Task 2 for translation highlighting).

Review (sonnet): spec ✅, code quality Approved with 1 Minor finding — `.known-highlight-static` was referenced in the JSX but never defined in `bloom.css` (traced to a gap in the plan's own CSS step, not an implementer deviation — the implementer correctly transcribed the brief verbatim). Fixed (commit `a039fe2`, `cursor: default`) and re-reviewed clean.

Task 1: complete (commits f496791..a039fe2, review clean after 1 trivial fix round).

## Task 2: vocabSuggestions.ts + VocabSuggestionsSection — complete

Implemented `includeTranslation` opt-in on both `apps/web/src/lib/vocabSuggestions.ts` (prompt/parse) and `apps/web/src/components/shared/VocabSuggestionsSection.tsx` (renders the translation via Task 1's `HighlightedText` static variant) in one commit (`6b97922`) — deliberately unsplit per the plan's own Part A/Part B instruction, since `parseVocabSuggestions`'s return-type change and its one call site's update are interdependent and splitting them would have left `tsc` broken between commits.

Review (sonnet) found 1 Important + 2 Minor. **Important**: the plan's own Step 3 prompt template (copied from Flutter's `word_radar_source.dart`, which always bakes in a trailing period) inserted a period into the `includeTranslation=false`/omitted path that the pre-Task-2 prompt never had — a real, verified byte-for-byte deviation from the Global Constraint that the 5 existing call sites' behavior must be unaffected. Traced by the reviewer directly against the pre-Task-2 git blob, not assumed. Root cause: a gap in the plan text itself (this session's plan-writer ported Flutter's punctuation without checking it against the pre-existing web prompt's own punctuation), not an implementer deviation.

Fixed (commit `b57b25f`): moved the period into the `translationReminder` string itself so the false-path output is period-free again (byte-for-byte identical to before), while the true-path still reads correctly. Re-review (sonnet) independently re-derived the original pre-Task-2 string from git history (not trusting either report's prose) and confirmed genuine byte-for-byte parity restored.

2 Minor findings logged, not fixed (both inert today, will matter once Task 3 is the first real `includeTranslation=true` consumer): (1) `VocabSuggestionsSection`'s `load()` resets `suggestions`/`error` on reload but never `translation` — a stale translation could flash briefly on a retry/reload once a real caller uses `includeTranslation`; (2) a pre-existing test title in `vocabSuggestions.test.ts` ("returns an empty array...") is now stale since the function returns an object, not a bare array — cosmetic only, inherited from the brief.

Task 2: complete (commits aa587fc..b57b25f, review clean after 1 fix round; 1 Important finding traced to a plan-text gap, not an implementer error, and fixed).

## Task 3: /reading/word-radar page — complete

Implemented `apps/web/src/app/(app)/reading/word-radar/page.tsx` + test (commit `3e6c46a`), consuming Task 1's `HighlightedText` (interactive variant) and Task 2's `VocabSuggestionsSection` (`includeTranslation`) — the first real caller of `includeTranslation=true`. Paste box (3000-char cap), instant local highlight of language-filtered known words, AI translation+suggestions when enabled, Vietnamese hint when not. Auth/settings gating matches `lookup/page.tsx`'s established pattern.

Review (sonnet) resolved a test-count red herring first: the brief's own prose said "7/7" but only 6 `it()` blocks actually existed in its Step 1 code — a pre-existing inconsistency in the brief document itself, not a dropped test or implementer gap (confirmed by counting the brief's actual test blocks directly). Then found 1 real Important issue: the page's subtitle spliced the English word "highlight" into an otherwise-Vietnamese sentence — traced to the plan's own Step 3 code (this session's plan-writer's mistake, not an implementer deviation), and flagged as inconsistent with every other page's pure-Vietnamese `scr-sub` subtitle in this app.

Fixed (commit `f1dbeff`): replaced "highlight" with "tô sáng". Re-review (haiku, appropriately cheap for a 1-line trivial fix) confirmed the sentence reads correctly and nothing else changed. 6/6 tests, tsc clean throughout.

Task 3: complete (commits 145c3ff..f1dbeff, review clean after 1 fix round; both findings traced to plan-authoring gaps, neither an implementer error).

## Task 4: Reading hub — 5th card — complete

Added "🔎 Quét từ vựng" card to `apps/web/src/app/(app)/reading/page.tsx` (commit `164a0ec`), navigating straight to `/reading/word-radar` via `router.push` — no `setMode`, no toggle-group styling, no mode/filter-footer involvement.

Review (haiku, appropriate for this small single-file mechanical task): spec ✅, code quality Approved, zero findings. Clean on first pass — no fix round. 17/17 reading hub tests, tsc clean.

Task 4: complete (commits 28b7652..164a0ec, review clean, no fix round).

All 4 tasks of the Word Radar plan are now implemented and individually reviewed. Next: final whole-branch review.

## Final whole-branch review — complete

Dispatched on opus (most capable available model), covering the full branch diff (13 commits, `05f8a5d..6bf7dc5` — MERGE_BASE = the commit right before the design spec was first committed).

Independently re-verified every ledger claim rather than trusting the narrative (byte-for-byte re-derived the Task 2 prompt-parity fix from git history and diffed both paths programmatically, compared the highlight algorithm line-by-line against the real Flutter source, benchmarked `splitIntoSpans`'s performance rather than assuming it was fine). Found the branch NOT ready to ship on the first pass — 4 Important findings invisible to any single task's own reviewer:

1. **Stale cross-scan state** — scanning a second piece of text doesn't remount `HighlightedText`/`VocabSuggestionsSection` (no `key`, same JSX position), so a stale translation from the FIRST scan stays on screen during/after the second scan's AI call — reproduced live by the reviewer, not just reasoned about.
2. **Translation over-highlighting** — the translation block highlighted meanings of the user's ENTIRE vocab bank (all known-language records) instead of only words that actually appear in the scanned text, diverging from Flutter's real behavior — reproduced live.
3. **Reading hub 5th card missing shared styling** — the new "Quét từ vựng" card used only the base `.reading-hub-card` class, but `cursor: pointer`/`font-family`/`text-align`/`border` all lived in the sibling-only `.reading-hub-card-toggle` class, so the new card rendered center-aligned with no pointer cursor and a visible border its siblings don't have — invisible to jsdom tests, only visible in the real rendered page.
4. **Popover clipped by the app shell** — `.main`'s `overflow-y: auto` makes it a clipping container on both axes; the popover's centered/upward positioning could push it past the container's unreachable left edge — traced to CSS overflow-axis computation rules, not assumed.

Dispatched ONE fix subagent (per skill guidance — not one per finding) covering all 4 Important + 6 Minor findings in a single commit (`e2426ef`): `scanId` + `key` remount strategy, filtered translation highlights to text-matched records only, moved shared button-reset CSS into the base hub-card class, repositioned the popover to open downward/left-aligned matching the existing `.vb-topic-popover` pattern, plus `white-space: pre-wrap` for pasted line breaks, a stale test title rename, and 3 new regression tests (second-scan staleness, translation-highlight filtering, an exact-string prompt-parity lock).

Re-review (opus): Approved. Went further than reading the diff — mutation-tested both behavioral fixes (temporarily reverted each, confirmed the new tests genuinely fail without the fix, restored), traced the CSS cascade specificity to prove the 4 pre-existing hub cards' appearance is unchanged, and confirmed the popover fix is a real equivalent (not just moved, genuinely un-clippable) by reasoning through `overflow-x`'s computed-value coupling to `overflow-y`.

**Verdict: Ready to ship.** 61/61 covering tests, 122/122 legacy-consumer tests, tsc clean. One nit logged (not fixed): `VocabSuggestionsSection`'s translation-highlight filter duplicates `findKnownHeadwords`'s matching logic inline instead of reusing it — cosmetic DRY opportunity, not a correctness issue.

# Quét từ vựng (Word Radar) on Web: PLAN COMPLETE

All 4 tasks implemented, individually reviewed (1 fix round each on Tasks 1, 2, 3; Task 4 passed clean on first review), and the whole branch passed final review after one fix round addressing 4 Important cross-task integration bugs that no single task's own review could have caught. This closes out the last remaining Flutter feature not yet ported to the React web app. 15 commits total (`2b30c37..e2426ef`). Nothing pushed to `origin/master` yet.

# LexiCore — Flutter: Drop Hive, Firestore-Direct + Mandatory Sign-In

## Task 1: VocabRepositoryImpl — Firestore-backed — complete

Rewrote `lib/features/vocabulary/data/repositories/vocab_repository_impl.dart` (commit `f59cda4`) against Firestore (`users/{uid}/vocab_records`, `users/{uid}/topics`), keeping the abstract `VocabRepository` interface completely unchanged so every existing consumer needs no changes. Added `fake_cloud_firestore` dev dependency for testing.

Review (sonnet): spec ✅, code quality Approved, zero findings — clean on first pass. Independently diffed the filter/reassignment logic against the original Hive implementation (`git show` of the pre-Task-1 commit) to confirm byte-for-byte behavioral parity, not just "looks reasonable." Confirmed topic seeding is atomic (1 batch, not 20 writes) and genuinely doesn't reseed on a second call (real test proving 21, not 40, after adding 1 custom topic).

Flagged for awareness (not a defect): `flutter analyze lib/` on the whole project is expected to stay red at `app_providers.dart:91` (`const VocabRepositoryImpl()` needs the now-required `uid`) until Task 4 wires up the signed-in-user DI — explicitly scoped there per the plan, not a Task 1 gap.

Task 1: complete (commits b0d7803..f59cda4, review clean, no fix round). 13/13 tests, flutter analyze clean on the touched file.

## Task 2: StatsService + notification scheduling — async — complete

Converted `StatsService.computeStats()` from a synchronous Hive-box scan to `Future<LearningStats>` reading via `VocabRepository.getAll()` (commit `7faa308`), rippled through `GetLearningStatsUseCase` and `notification_notifier.dart`'s `_computeNextDueAt()`.

Implementer went one step beyond the brief's literal Step 3 code: also converted `app_providers.dart`'s `learningStatsProvider` from sync `LearningStats` to `Future<LearningStats>` — necessary because `computeStats()` becoming async otherwise makes `app_providers.dart` itself fail to compile (Dart doesn't implicitly unwrap Futures), a plan gap since Task 2's own brief only showed the change reaching Task 3's file, not the ripple back into the DI file Task 2 was already editing. Also fixed a real bug in the brief's own verbatim test fixture (2 records missing `nextReviewAt` would default to "due," silently breaking the asserted `dueCount: 2`).

Review (sonnet) independently verified both extras rather than trusting the report: reverted the `learningStatsProvider` fix to reproduce the exact compile error and confirm it was forced not optional; hand-traced the corrected test fixture to confirm `dueCount: 2` genuinely holds. Confirmed via `git show`/`git stash` that the one remaining `app_providers.dart` error (`VocabRepositoryImpl` missing `uid`) predates this task (Task 1's deliberate deferral to Task 4/5).

Spec: ✅. Code quality: Approved. 1 Minor logged, not fixed: `reschedule()` has no try/catch at 2 of its 3 call sites (`NotificationNotifier.build()`'s microtask/listener, `app_shell.dart`'s lifecycle callback) — pre-existing gap, not introduced by this task, but risk is now materially higher since the underlying calls hit live Firestore instead of local Hive. Flagged for the final whole-branch review to triage against the plan's "async failures must be caught, no crash" global constraint.

Task 2: complete (commits 71b4569..7faa308, review clean, no fix round). 4/4 tests, flutter analyze confined to the 2 files explicitly deferred to Task 3 plus the pre-existing Task-1-deferred uid error.

## Task 3: Async-aware progress/practice screens — complete

Updated `progress_screen.dart` (`AsyncValue<LearningStats>` via `.when(loading/error/data)`, Vietnamese error message) and `practice_home_screen.dart` (due-count badge properly awaited with `mounted` guards before/after the async gap, best-effort silent-fail-to-0 on error) — commit `35d6a87`.

Implementer correctly detected Task 2's implementer had already converted `app_providers.dart`'s `learningStatsProvider` (a necessary side effect noted in Task 2's own ledger entry) and left it untouched rather than re-doing/conflicting with already-correct work — confirmed by the reviewer as a genuinely empty diff on that file.

Review (sonnet) went beyond count-matching on the "32 pre-existing test failures, zero new" claim: checked out the pre-Task-3 baseline, extracted the actual failing test IDENTITIES (not just the count) from both runs, and confirmed byte-identical failure sets — ruling out a hidden pass↔fail swap that a bare count match could have masked. Also diffed `progress_screen.dart`'s `data:` branch against its pre-Task-3 version to confirm the real UI logic is unchanged, only the async wrapping is new.

Spec: ✅. Code quality: Approved. Zero findings — clean on first pass, no fix round (2nd task in this plan to pass clean first-try, after Task 1).

Task 3: complete (commits ed28a02..35d6a87, review clean, no fix round).

## Task 4: Mandatory sign-in + one-time Hive→Firestore migration — complete

**Implementer subagent was cut off mid-task by a session API limit**, after writing all code/tests but before committing. Controller (this session) inspected the staged changes directly, ran the test suite (10/10 new, 497/497 full) and `flutter analyze` (0 errors) independently, fixed one trivial unused-import warning, wrote the task report itself, and committed as `118274b`.

Given the stakes (mandatory auth gating + irreplaceable-user-data migration), dispatched the review on opus rather than the session's usual sonnet tier. **This paid off**: the review found 2 Critical bugs that together meant the data-safety net didn't actually work end-to-end, despite 497/497 tests passing and 0 analyze errors —
- **C1**: GoRouter's redirect fired (navigating away from `/sign-in`) almost immediately after `signInWithGoogle()` succeeded, via the auth-state-stream listener — while the migration was still awaiting network I/O. The sign-in screen got disposed mid-flight, silently swallowing any migration failure with zero visible error and no retry path, directly violating the plan's explicit "migration failure must show an error + retry" requirement.
- **C2 (cross-task)**: the sign-in screen's `Hive.box<String>(...)` calls require the boxes to already be open, but Task 5 (later in this same plan) removes the `main.dart` code that opens them — a genuine plan self-contradiction that would have made the entire migration path start silently throwing (and, per C1, silently swallowing that throw) as soon as Task 5 landed.
Plus 2 Important findings (I1: checked the wrong/lagging source of truth for "is the user signed in," could skip migration entirely; I2: migration wasn't tracked as done, so a second sign-in — same or different device — could blind-overwrite newer Firestore data with stale local Hive data before destructively clearing it) and several Minor findings.

Dispatched one fix subagent for all findings together (commit `44acf55`): decoupled "signed in" from "navigate away from sign-in screen" (only `/splash` auto-redirects now; `/sign-in` navigates away only after its own migration step settles), rewrote the sign-in screen as an explicit idle/signingIn/migrating state machine with a real "Thử lại" retry button, made `HiveMigrationService` self-contained (opens its own Hive boxes rather than depending on `main.dart`), switched to `FirebaseAuth.instance.currentUser` as the consistent source of truth, and added a per-uid SharedPreferences "already migrated" flag.

Re-review (opus) verified every fix by tracing the actual failure scenario again rather than trusting the fix report — including reading the installed `hive`/`hive_flutter` package source to independently confirm `Hive.openBox`/`initFlutter` are genuinely idempotent (the load-bearing claim behind C2's fix), and confirming I2's new test would actually fail without the flag (not just that a flag exists). Found the M1 test's own justification was factually wrong (two pre-existing tests already caught that particular precedence bug) even though the test itself was fine to keep. **Verdict: Approved, safe to consider Task 4 complete.**

Re-reviewer also flagged that Task 4's fix round left Task 5's own plan text stale in 3 places (Step 1's grep expectations, Step 4 being already-done, Step 7's "last legitimate Hive usage" file list) — controller updated `docs/superpowers/plans/2026-08-27-flutter-drop-hive.md` accordingly (commit `5982d2f`) before dispatching Task 5, to prevent its implementer from halting incorrectly or redoing already-complete work.

Task 4: complete (commits b77fc9c..44acf55, review clean after 1 fix round — the most significant fix round of this whole plan, 2 genuine Critical data-safety bugs caught only because the review was dispatched on the most capable available model rather than the usual mid-tier default).

## Task 5: Delete SyncService/SyncNotifier, cleanup — complete

Deleted `sync_service.dart`/its test and `sync_notifier.dart`/its generated file (commit `4607c2d`), removed Hive init from `main.dart`, cleaned up `settings_screen.dart`'s now-unreachable "not signed in" branch (`_SignedOutCard` deleted) and sync-status UI (`_SignedInSection` no longer takes `syncStatus`). Correctly confirmed Task 4 had already wired `vocabRepositoryProvider` and correctly left `pubspec.yaml`'s `hive`/`hive_flutter` untouched (still needed permanently by `hive_migration_service.dart`).

Review (sonnet): spec ✅, code quality Approved, zero findings — clean on first pass (3rd task this plan to pass clean first-try). Independently grepped the whole `lib/`/`test/` tree for any remaining `SyncService`/`SyncNotifier`/`SyncStatus`/`syncNotifierProvider` reference (found none — 2 harmless substring false-positives only) and verified the 499→497 test-count drop is fully explained by deleting `sync_service_test.dart`'s exactly-2 tests, no other file's count silently changed.

Task 5: complete (commits 0508206..4607c2d, review clean, no fix round).

# LexiCore — Flutter: Drop Hive, Firestore-Direct + Mandatory Sign-In: ALL 5 TASKS COMPLETE

Next: final whole-branch review on the most capable available model, per skill guidance — this plan's Task 4 already demonstrated the value of that (2 genuine Critical bugs a mid-tier reviewer likely would have missed), so hold the same bar for the final pass.

## Final whole-branch review — complete

Dispatched on opus (most capable available model), covering the full branch diff (14 commits, `70ac258..274ab01` — MERGE_BASE = the commit right before the design spec was first committed).

Independently re-verified rather than trusting the ledger: re-ran `flutter analyze`/`flutter test`, traced the full sign-in→migration→first-screen flow end-to-end (not just each task's own diff in isolation), re-confirmed Task 4's two Critical fixes still hold after Task 5's later deletions by checking `Hive.initFlutter()`'s actual resolved directory path matches between `main.dart`'s old call and `HiveMigrationService`'s new self-contained call, and grepped the whole tree for any remaining synchronous vocab-data assumption outside the plan's enumerated files.

**First pass found the branch NOT ready to ship** — 1 Critical + 2 Important + 2 Minor, all invisible to 497/497 passing tests and 0 analyzer errors (the 3rd time in this plan a clean-tests signal hid a real bug — Task 2's implementer catching a compile gap, Task 4's Criticals, now this):
- **Critical**: `settings_screen.dart`'s `user!` force-unwrap crashes with a null-check exception on every sign-out — Task 5 removed the "signed out" branch on the premise sign-in is mandatory, but signing OUT is exactly what makes the auth stream emit null while the screen is still mounted during the router's exit transition. **Empirically reproduced** with a real widget test (built, ran, confirmed the crash, then removed the scratch file) rather than just reasoned about.
- **Important**: `reschedule()` (notification scheduling) now depends on live Firestore reads but was only try/catch-guarded at 1 of 4 real call sites — a Firestore failure on the other 3 (settings-change listener, build-time microtask, app-lifecycle resume) became an unhandled async exception, violating the plan's own "async failures must be caught, no crash" constraint. This was Task 2's own deferred Minor finding, escalated here since the risk profile genuinely changed (network vs. local reads).
- **Important**: the one-time migration's per-uid "already migrated" flag only guarded against *repeat* migrations on the same install — it didn't distinguish a never-signed-in user (Hive is their only copy, must migrate) from a previously-signed-in user whose Hive is a stale local mirror from the old SyncService (must NOT migrate, since a blind push would silently revert Firestore-side edits/deletions made since, e.g., from `apps/web/`).
- 2 Minor: `reschedule()` reading the vocab collection twice per call; one corrupt Hive record aborting the entire migration instead of being skipped.

Dispatched one fix subagent for all 5 findings (commit `e585b41`): null-safe branch restored in `settings_screen.dart`; `reschedule()`'s entire body wrapped in try/catch at the source so all 4 call sites are protected regardless of whether each one awaits/catches it (also fixed the double-fetch by deriving both due-count and next-due-date from one `getAll()` call, with the due-count predicate verified character-for-character identical to `StatsService.computeStats()`'s own); migration now checks whether the user's Firestore `vocab_records` collection already has any documents BEFORE touching Hive at all, skipping the push (and leaving Hive untouched, not cleared) if so; both batch-push loops now catch per-record errors and skip just the bad record.

Re-review (opus): Approved, "ready to ship as-is." Re-reproduced the Critical 1 fix empirically (reverted just that hunk, confirmed the crash comes back; restored, confirmed it's gone) rather than trusting the diff looked right. Verified the new migration-guard test genuinely proves the fix (pre-seeded Firestore doc survives untouched, Hive left uncleared). 499/499 tests, 0 analyzer errors/warnings.

5 non-blocking observations logged (not fixed, explicitly "narrow"/"defensible trade-off" by the reviewer's own assessment):
1. The 500-doc batch-commit boundary sits inside the new per-record try/catch — if that specific commit throws, `count` never resets, batches grow unbounded past Firestore's 500-write cap on the final commit. Requires >500 records AND a mid-batch commit failure; end-user outcome unchanged (migration fails safely, error+retry shown, Hive/flag untouched) — just a misleading error surfaced in that narrow case.
2. If every record in a non-empty Hive box is malformed, the migration still clears Hive and reports success (nothing decodable was recoverable anyway, but worth a `pushedAny` guard around the clear if ever revisited).
3. The Firestore-already-populated guard only checks `vocab_records`, not `topics` — a user with topics but zero vocab (e.g. deleted all words on web) would still get their stale Hive pushed. Reviewer assessed this as the correct trade-off (checking topics too would wrongly skip legitimate migrations for topics-only accounts), not a bug to fix.
4. Generated Riverpod `.g.dart` hash comments drifted out of sync (debug-only hot-reload metadata, zero release/test impact) — a `build_runner` run before merge would tidy this, not required.
5. No regression test exists for the Critical 1 sign-out crash specifically (only caught via the reviewer's own empirical widget test, which was written and then removed as scratch) — reviewer offered to add it permanently but left it as the controller's call; not added, logged as a good candidate for a future small test-coverage pass given this exact bug class already shipped once in this plan.

**Verdict: Ready to ship.**

# LexiCore — Flutter: Drop Hive, Firestore-Direct + Mandatory Sign-In: PLAN COMPLETE

All 5 tasks implemented and individually reviewed (1 fix round each on Tasks 2 — self-caught by the implementer — and 4 — the plan's most significant fix round, 2 genuine Critical data-safety bugs; Tasks 1, 3, 5 passed clean), plus the final whole-branch review's own fix round (1 Critical + 2 Important + 2 Minor, none of them visible to passing tests/clean analyze — the review process itself, not the test suite, is what caught every real bug in this entire plan). 16 commits total (`6d5ee86..e585b41`). Nothing pushed to `origin/master` yet.

This plan's own history is worth remembering: 3 separate times (Task 2's async-provider gap, Task 4's 2 Criticals, the final review's 1 Critical + 2 Important), a fully-green `flutter test`/`flutter analyze` signal coexisted with a real, user-facing bug. Every one of them was caught by a careful reviewer tracing actual failure scenarios rather than trusting green CI — reinforcing that for auth/data-migration-sensitive work, dispatching review on the most capable available model (not the session's usual mid-tier default) is worth the cost.

# LexiCore — Tách vocab_records theo ngôn ngữ mục tiêu

## Task 1: Web — vocabRecords.ts + all 13 call sites — complete

Split `users/{uid}/vocab_records` into `users/{uid}/vocab_records_{language}` on the web app (commit `816cc94`) — `language` now required on every read/write function, updated across all 13 call sites (Dashboard, Vocab Bank, Practice, Reading×4, Listening×2, Word Radar, VocabRecordCount) in the same commit to keep the repo compiling throughout.

Implementer caught 3 real gaps the plan itself missed: (1) 4 files the plan claimed already had `settings`/`useSettingsContext()` in scope (`dashboard`, `vocab-bank`, `practice`, `reading` hub) actually didn't; (2) 2 test files outside the plan's own file list broke as ripple effects (`VocabRecordCount.test.tsx`, `dev/verify/page.test.tsx`); (3) most importantly, a genuine correctness bug the plan's own literal code would have shipped — `settings` starts `null` and resolves asynchronously, so applying the plan's `getVocabRecords(user.uid, settings.targetLanguage)` edits verbatim without a `!settings` guard would throw a null-deref on first mount for every signed-in user on 12 pages. Fixed proactively by the implementer, not left for review to catch.

Review (opus, given the blast radius — virtually every page in the app) independently traced all 13 null-guard sites, confirmed no wrong-collection-write risk (mutation call sites correctly source `language` from the loaded record, not from possibly-stale `settings`), and found 1 more real Important bug the implementer's own fix had introduced: `/dev/verify` (outside the `(app)` route group, no `SettingsProvider` in its layout) now throws on every visit since `VocabRecordCount` calls `useSettingsContext()` unconditionally — and the commit's own test "fix" papered over this by mocking away `SettingsContext` entirely, passing without ever exercising the real broken path.

Fixed (commit `b38069d`): added `apps/web/src/app/dev/layout.tsx` wrapping the dev routes in `SettingsProvider` (matching `(app)/layout.tsx`'s exact pattern), and rewrote the test to mock one level lower (`useAuthUser`/`useSettings`) so it exercises the real `SettingsProvider`/`useSettingsContext` wiring instead of stubbing it away. Re-review (sonnet) verified this empirically — reverted the layout fix, confirmed the test fails with the exact original error, restored it, confirmed it passes.

5 Minor findings logged, not fixed: test coverage doesn't distinguish correct record-sourced language from incorrect settings-sourced language (fixture happens to make both "english"); the null-guard fix itself has no regression test on the 4 newly-guarded pages; 2 leftover now-redundant `targetLanguage === "english"` filters in `listening/page.tsx`/`listening/dictation/page.tsx` (same class of dead code Word Radar's own filter removal addressed, just missed on these 2); a stale-settings transient wrong-language fetch right after sign-in (pre-existing `useSettings` behavior, now visible on vocab fetches); collection-path-string duplicated 4× in `vocabRecords.ts` (matches the plan's own prescribed code, not a deviation).

**Operational note, outside this diff, flagged by the reviewer as gating deploy (not a code defect):** no `firestore.rules` file exists in this repo (Console-managed) — if the live rule matches the old `/users/{uid}/vocab_records/{doc}` path literally rather than a `{document=**}` wildcard, every new `vocab_records_{language}` collection would be permission-denied for every user. Also: this commit alone (before Task 3's migration script runs) points the web app at collections that don't exist in production yet — do not deploy web until the migration script (Task 3) has run.

Task 1: complete (commits cdde6cd..b38069d, review clean after 1 fix round). 724/724 tests, tsc clean.

## Task 2: Flutter — VocabRepository/VocabRepositoryImpl/StatsService/use cases + all call sites — complete

Split `vocab_records` into per-language collections on Flutter (commit `3bc3895`) — `getAll`/`getById`/`delete` now require `language`, `save`/`update` route via `record.targetLanguage`, `deleteTopic()` loops `Language.values` for cross-language reassignment (since `topics` stays shared but `vocab_records` is now split).

**Note on process**: the first implementer dispatch was interrupted mid-task by a session limit. Re-dispatching found the brief's prescribed edits already present, uncommitted, in the working tree from the interrupted attempt — verified each by reading the actual files (not trusting the interrupted state), found and fixed one additional real bug (`dictation_result_screen_test.dart` silently passing with 0 actual SM-2 updates due to an unoverridden `sharedPreferencesProvider` throw being swallowed by the screen's own best-effort catch), then committed everything as one commit.

Review (opus) found the brief's own Files list had missed ~12 files (2 real production screens — `practice_home_screen.dart`, `progress_screen.dart` — plus ~10 test files) — all independently verified as correctly fixed, not just made to compile. Found 2 genuine Important bugs:
1. **SM-2 updates silently stopped when a dictation/reading session's language differed from the global Settings target language** — `dictation_home_screen.dart`/`reading_home_screen.dart` have their own LOCAL per-session language picker independent of global settings, but the result screens now resolved session words against the newly-settings-scoped `vocabBankNotifierProvider`. A session in a non-default language made every lookup throw, silently swallowed, producing zero SM-2 writes with the UI showing success — permanently breaking spaced repetition for that language's words, with the streak looking healthy throughout.
2. **`HiveMigrationService` still wrote into the dead flat `vocab_records` collection** instead of per-language ones — a real migration would push data nowhere the app reads, then clear local Hive, causing invisible permanent data loss (mitigated only as an accident of the "keep original collection as backup" policy, not a deliberate protection).

**Fix round 1** (commit `82f9496`): threaded the session's actual language through to both result screens (`getVocabListUseCaseProvider(language: sessionLanguage)` instead of the globally-scoped provider); routed the migration's vocab writes through `VocabRepositoryImpl.save()` instead of raw flat-collection batch writes.

**Re-review (opus) found fix round 1 introduced 2 new problems**: (a) the migration fix moved `save()` INSIDE the same per-record catch meant only for malformed-JSON skips — a genuine Firestore WRITE failure (permission-denied, network) now got silently swallowed too, with Hive still cleared and success still reported, reintroducing permanent data loss via a different path than the original bug; (b) a new `vocabListForLanguageProvider` (added to support the session-language fix) was a plain non-invalidating `FutureProvider.family`, caching forever and never reflecting new saves — a real regression from the previous unfiltered-but-always-fresh `vocabBankProvider`.

**Fix round 2** (commits `77532cf` + `84ada0e` — note: this round's implementer subagent stalled on a background test run mid-task; the controller inspected its already-correct uncommitted work directly, ran the verification itself, and committed): moved `save()` outside the parse-only catch so a write failure now propagates to the sign-in screen's existing error+retry UI instead of being swallowed; made `vocabListForLanguageProvider` `.autoDispose` and watch `vocabBankNotifierProvider` for invalidation-on-mutation; strengthened 2 migration tests that could previously pass with a hardcoded-English implementation.

**Re-review (opus) of round 2**: Approved, with rigorous mutation-testing on every claim — reverted each fix individually and confirmed each corresponding test genuinely fails without it (including confirming the invalidation test isolates the `ref.watch(vocabBankNotifierProvider)` dependency specifically, not just `.autoDispose`'s GC behavior). Found 1 new Minor, logged not fixed: a mid-loop migration failure (succeeds on records #1-4, throws on #5) leaves #1-4 durably written to Firestore; a retry then sees "this uid already has vocab data" and concludes it's a returning-user stale-mirror case, permanently skipping records #5+ with the migrated flag set and no error shown. Narrow (requires failure after at least one success, in an already-small legacy never-signed-in cohort) and strictly better than the bug it replaced (no active data loss, just an incomplete migration) — reviewer explicitly framed this as a judgment call, not a required fix.

Task 2: complete (commits 1763967..84ada0e, review clean after 2 fix rounds — both rounds found genuine Important-severity data-correctness/data-safety bugs that a fully passing test suite and clean analyze did not surface).

## Task 3: Migration script for real production data — complete

Standalone Node.js script (`scripts/migrate-vocab-records-per-language.js`) migrating each user's flat `vocab_records` into `vocab_records_{language}` subcollections, keyed by each record's own `targetLanguage`. Developed test-first against the Firestore emulator.

**Note on process**: the implementer subagent was interrupted mid-task by a session limit, but had already committed working code (`5627e76`) with 4/4 tests passing per its own commit message. The controller independently verified this by getting the Firestore emulator running locally (adding a `firestore` emulator port to `firebase.json`, commit `7d404d2`, since none was configured) and re-running the tests live rather than trusting the interrupted agent's unwitnessed claim.

The implementer made 2 deliberate, well-reasoned deviations from the plan's own reference implementation, both confirmed correct by the eventual review: (1) discovers users via `collectionGroup("vocab_records")` instead of listing the top-level `users` collection, because this app's data model never materializes a `users/{uid}` parent document (confirmed by grep across both apps AND by checking the original bulk-import script that created the real 290+ records — it never wrote a parent doc either) — the plan's own reference code would have silently found `users: 0` against real production data and reported a clean-looking false success while migrating nothing; (2) skips (never overwrites) a destination document that already exists, since Tasks 1-2 have already shipped and a real user could write genuinely-new records into the per-language collections before this script ever runs.

Review (opus) independently verified deviation #1 with an emulator probe reproducing the exact silent-failure the plan's reference code would have hit, and traced deviation #2's correctness. Found 2 Important + several Minor: (1) no target-environment guard — a stray `FIRESTORE_EMULATOR_HOST` or wrong ADC project could reproduce the same silent-false-success bug the deviation just fixed, with the operator reading "0 migrated" as "nothing to do" instead of "something's misconfigured"; (2) neither deviation had dedicated test coverage — the existing 4 tests would stay green even if a future change reverted either one.

Fixed (commit `6c891ba`): CLI entry-point now logs the resolved project id + emulator-host state before any writes, and treats `users === 0` as a loud, non-zero-exit failure rather than silent success (exported `migrateVocabRecords()` itself unchanged, so test fixtures using `users: 0` intentionally still work). Added 2 tests: one proving discovery works with no `users/{uid}` parent doc ever created (by also asserting `db.collection("users").get()` returns empty in the same setup — proving by contrast a naive implementation would fail there), one proving an existing destination document survives untouched on a second run.

Re-review (sonnet): Approved, 6/6 tests, both new tests verified to assert the specific behavior claimed (not just "no error thrown"). Noted the test file has no fixture cleanup/teardown, so re-running against the same long-lived local emulator instance across sessions (rather than a fresh one) can produce spurious failures from stale prior-run data — logged as a minor test-hygiene gap, not a script defect, not fixed.

**Final verdict on the script itself: safe to run against real production data as shipped** — strictly additive (only `batch.set()`s to a destination just verified not to exist), never deletes/modifies the source `vocab_records` collection, so the worst realistic failure mode is surplus documents in the new collections, individually cleanable, with the original ~290+ records untouched by any code path.

Task 3: complete (commits 81f90aa..6c891ba, review clean after 1 fix round). 6/6 tests, verified live against the Firestore emulator (not just trusted from a report) at every stage.

# LexiCore — Tách vocab_records theo ngôn ngữ mục tiêu: ALL 3 TASKS COMPLETE

Next: final whole-branch review, then the manual production migration + deploy sequence (code first, then run this script against real Firestore, then deploy Flutter Web + React web together) — per the spec's explicit deploy-sequencing decision, running the script against real data is a deliberate manual step outside this plan's own automated task execution.

## Final whole-branch review — complete

Dispatched on opus (most capable available model), covering the full branch diff (14 commits, `cad46e7..ab54970` — MERGE_BASE = the commit right before the design spec was first committed).

Independently re-verified every claim in the ledger rather than trusting the narrative, given how many fix rounds this plan took: traced 2 concrete end-to-end scenarios across BOTH platforms (a web-saved English word round-tripping correctly to Flutter's read path and back), confirmed Dart's `Language.name` and web's `TargetLanguage` string produce byte-identical collection-path segments for all 5 languages, mutation-tested Task 2's provider-invalidation fix a SECOND time (independently of that task's own re-review) by deleting the `ref.watch` again and confirming the exact same stale-cache symptom reappears, and grepped the entire repo for every remaining `vocab_records` reference and manually classified each one (none were a live bug — all either correctly per-language, the migration script's deliberate read of the old flat collection, or stale-but-harmless documentation/dead one-off scripts).

Also independently confirmed the real production data's actual shape matches what the migration script expects: read `scripts/import-vocab/import.js` (the script that originally created the ~290 real records) and confirmed every record was written with `targetLanguage: 'english'` and `id` matching its own doc id — meaning the migration should see ~290 migrated, 0 skipped, against real data.

**Verdict: Ready to ship, no fix round needed.** Zero Critical/Important findings. 6 Minor findings logged, none blocking: stale README Firestore-schema docs (still shows the flat collection); 2 already-run one-off import scripts still targeting the flat collection (self-labeled "delete this folder" already); a few leftover now-redundant language filters analogous to the one Word Radar's own task removed; a stale code comment citing the now-deleted `sync_service.dart` as the reason `id` is written into the document body (the behavior is still required for a different reason — `VocabRecord.fromJson`'s non-nullable `id` read — just the comment's citation is outdated); a minor double-fetch efficiency note in `vocabListForLanguageProvider`.

**One operational pre-flight gate flagged, not a code defect, still unresolved**: no `firestore.rules` file exists in this repo (Console-managed) — if the live production rule matches `/users/{uid}/vocab_records/{doc}` literally rather than via a `{document=**}` wildcard, every new `vocab_records_{language}` collection would be permission-denied for every user on both apps immediately after deploy, and the failure would be silent from the app's perspective (both surfaces would just look empty, with a Dashboard/Vocab Bank showing "0 words"). This was first raised in Task 1's own review and never independently closed out since it requires a Firebase Console check the coding tasks cannot perform. **Recommended order before running anything against real data: (1) verify/patch the Console-managed Firestore rules use a wildcard match on `vocab_records_*` paths → (2) run `node scripts/migrate-vocab-records-per-language.js` against real production, expecting ~290 migrated / 0 skipped / 1 user, confirming the logged project id says `lexi-core` and the emulator-host line says "(not set)" → (3) deploy Flutter Web and the React web app together → (4) manually confirm both surfaces show real data correctly before ever considering the old flat `vocab_records` collection safe to delete.**

# LexiCore — Tách vocab_records theo ngôn ngữ mục tiêu: PLAN COMPLETE

All 3 tasks implemented and individually reviewed (1 fix round on Task 1, 2 fix rounds on Task 2 — the most eventful task in this plan, with round 1's own fix introducing 2 new bugs that round 2 had to fix — 1 fix round on Task 3), plus a final whole-branch review that found zero new Critical/Important issues after independently re-tracing the whole history rather than trusting a green test suite. 16 commits total (`c70d507..0581a02`). Nothing pushed to `origin/master` yet. The manual production migration + coordinated deploy is a deliberate next step outside this plan's own automated task execution, gated on a Firestore-rules check this session cannot perform.

# LexiCore — Flutter AI Settings Firestore Sync

## Task 1: Rewire AI calls through the Cloud Function; ciphertext-only key storage — complete

`ProviderConfig.apiKey` (plaintext) renamed to `apiKeyCiphertext` (nullable KMS ciphertext) across the domain entity, `UserSettingsState.defaults`, `UserSettingsNotifier`, and the Settings screen. `AiClientFactory` rewritten: `_GeminiClient`/`_OpenAiClient` deleted, replaced by `_CloudFunctionClient` calling the `generateContent` Cloud Function through a new injectable `CloudFunctionCaller` seam (`lib/core/services/cloud_function_caller.dart`) — matches this codebase's established pattern of testing through an injected interface rather than mocking the Firebase SDK's concrete classes. Added `AiProviderX.cloudId`/`aiProviderFromCloudId` for the `openRouter` -> `"openrouter"` lowercase mapping the Cloud Function expects. Added `ApiKeyEncryptor` (`lib/core/services/encrypt_api_key.dart`) wrapping `encryptApiKey`; the Settings screen's API-key dialog now encrypts before saving, shows a blocking Vietnamese error on failure, and never pre-fills the field with a real key (mirrors `apps/web/src/components/settings/AiProviderSection.tsx`'s `handleUpdateKey` exactly).

Implementer: haiku (fully mechanical — every file's exact content was given verbatim in the brief). 505/505 tests pass. Review (sonnet): spec-compliant, zero Critical/Important findings. One ⚠️ item (are the 21 `flutter analyze` warnings genuinely pre-existing and unrelated?) independently confirmed by the controller — all 21 are `RadioListTile.groupValue`/`onChanged` Flutter-SDK deprecation infos, none touching any file this task's diff changed. 3 Minor findings logged, none fixed (all cosmetic): a UTF-8 BOM on 4 newly-created files; the generic Vietnamese encryption-error string duplicated verbatim between `encrypt_api_key.dart` and `settings_screen.dart` (plan-mandated — the brief's own Step 13 code has this duplication).

Task 1: complete (commit de34c73..080112c, review clean). 505/505 tests.

## Task 2: Firestore settings sync — bootstrap fetch/migrate + push-on-change — complete

New `AiSettingsSyncService` (`lib/core/services/ai_settings_sync_service.dart`): one-shot `bootstrapSync(uid, notifier)` fetches `users/{uid}/settings/config` (same document/field names `apps/web/src/lib/settings.ts` uses), remote-wins onto `UserSettingsNotifier` via its existing setters called with a new `sync: false` flag (to avoid re-pushing what was just read), then migrates any local pre-encryption plaintext key Firestore had nothing for; `pushProviderSettings(...)` does a best-effort `SetOptions(merge: true)` write, called from the notifier's `setActiveProvider`/`setProviderConfig`/`setTargetLanguage` (default `sync: true`) via a new `_pushBestEffort()` that never throws. `legacyPlaintextApiKey()` added to `UserSettingsNotifier` to recover a still-plaintext key from the pre-Task-1 JSON shape for that one-time migration. Wired into `sign_in_screen.dart` right after the existing Hive migration, deliberately with no try/catch (best-effort, never blocks navigation).

Implementer: haiku. Review (opus, given the data-sync-safety stakes): task quality Approved, zero Critical. One Important finding that was **entirely about report honesty, not code correctness**: the implementer silently added a fake `ApiKeyEncryptor`/`CloudFunctionCaller` to 2 test files' `_FakeAiSettingsSyncService`/`AiSettingsSyncService` constructions (7 call sites) — a deviation from the brief's literal text — while its own report asserted "no deviation from brief scope" four separate times. The controller had independently caught part of this (and one separate false-positive suspicion about missing ignore-comments, which the reviewer confirmed WAS a controller error — the comments did exist, just not matching the controller's grep pattern) before dispatching the review. **The code deviation itself was verified correct and necessary**: the brief's own `_FakeAiSettingsSyncService` example only guarded against `FirebaseFirestore.instance` throwing pre-Firebase-init in a plain unit test, missing that `ApiKeyEncryptor()`'s default (`FirebaseCloudFunctionCaller()` → `FirebaseFunctions.instanceFor(...)`) has the identical failure mode — a real gap in the plan/brief, not an implementer mistake. Also caught the same review pass: a genuine Important **code** bug — `bootstrapSync`'s remote-wins logic would silently blank a real local-only API key with `null` whenever `apps/web/`'s `saveSettings` writes its full (non-merged) settings document, which includes `apiKeyCiphertext: null` for every provider the web user hasn't configured, for a completely unrelated field change.

**Fix round 1** (commit `dd2f14e`): guarded the remote-wins branch to only apply when the remote `apiKeyCiphertext` is non-null and non-empty, falling through to the legacy-migration check otherwise (same as "no remote entry"); added a TDD-verified regression test (RED confirmed against the pre-fix code, then GREEN). Also fixed a Minor finding in the same round: added a missing `if (!mounted) return;` guard before the two post-await `ref.read` calls in `sign_in_screen.dart`, matching the pattern already used earlier in the same method.

Re-review (sonnet): confirmed both fixes correct and complete, traced the rest of `bootstrapSync`/`pushProviderSettings` for the same null-blanking bug class and found no other instance, confirmed the new test is genuine (not a weaker shape that would pass even with the bug present) and the existing 6 tests untouched. Zero new findings.

Task 2: complete (commits a1e0936..dd2f14e, review clean after 1 fix round). 519/519 tests.

# LexiCore — Flutter AI Settings Firestore Sync: ALL TASKS COMPLETE

Next: final whole-branch review.

## Final whole-branch review — complete (2 fix rounds)

Dispatched on opus (most capable available model) over the full branch diff (7 commits, `2646a7f..010b489` for the first pass). Independently traced the plaintext-key flow end-to-end (dialog → encrypt → local write → push → Firestore, confirmed no raw key ever persisted anywhere), verified all 9 AI data sources are genuinely untouched (they only ever depend on `GenerativeModelClient.generateContent`), verified field-name/enum-string parity against `apps/web/src/lib/settings.ts`/`languages.ts`/`functions/src/generateContent.ts` for all 3 providers and all 5 languages, and confirmed the sync-scope boundary (`activeContext`/`aiEnabled`/`targetCefrLevel`/`reminder*`/`theme`/`fontSize`) held with zero leakage.

**Found 1 Critical + 3 Important, all real, requiring 2 further fix rounds:**

1. **Critical: `bootstrapSync` was unreachable for the one real production user.** Its only call site was `sign_in_screen.dart`, but mandatory sign-in (shipped earlier this session) means an already-authenticated user's session persists — `app_router.dart`'s redirect sends them from `/splash` straight to `/`, never back through `/sign-in`. The one-time legacy-plaintext-key migration, and any future pull-sync from web, would never run again after the branch's very first sign-in — silently breaking every AI feature for the real user on first use, since their key sits in the old plaintext shape `ProviderConfig.fromJson` no longer reads.
2. **Important: `pushProviderSettings` could blank a real remote key from the write side** — symmetric to the null-blanking bug Task 2's own fix round had already closed on the *read* side. It always wrote `apiKeyCiphertext` even when null; under Firestore's `merge:true` deep-merge, an explicit `null` overwrites a real value saved from another device/platform.
3. **Important: `currentUidProvider` was `keepAlive`, caching the uid forever** — sign-out then sign-in as a different account in the same session would keep pushing to the previous user's Firestore document.
4. **Minor (real, fixed anyway): a Task 1 brief mistakenly called `ai_provider_test.dart` a new file and gave a 5-test replacement, silently deleting 12 pre-existing tests** (labels/baseUrl/defaultModel/modelPresets/an invariant check) that the file already had before this branch.

**Fix round 1** (commit `458eba8`): added a `_SplashScreen` stateful widget that fires `bootstrapSync` on every app launch when already signed in (fixes #1 for mobile — see round 2); guarded `pushProviderSettings` to omit `apiKeyCiphertext` from the payload map entirely when null/empty instead of writing an explicit null (fixes #2, with a TDD-verified regression test); changed `currentUidProvider` from `keepAlive` to a normal auto-dispose provider so it re-reads `FirebaseAuth.instance.currentUser` on every access (fixes #3, verified against Riverpod 2.6.1's own dispose semantics in the re-review rather than a runtime test, since this codebase has no `FirebaseAuth` fake seam); restored the 12 deleted tests alongside the 5 newer ones in `ai_provider_test.dart` (18 total, fixes #4). The fix implementer independently caught and corrected an inconsistency in the controller's own dispatch (a test snippet missing a required `encryptor:` fake, which every sibling test in that file already needed for the identical `FirebaseFunctions.instanceFor(...)`-throws-pre-init reason already documented from Task 2's fix round) — reported honestly this time, unlike the earlier round's report-honesty issue.

**Re-review (opus)** confirmed fixes #2/#3/#4 fully correct, and confirmed the fixer's self-flagged `encryptor:` addition was accurate and necessary (both pre-existing sibling tests already needed it — the dispatch's premise that they didn't was simply wrong). **Found fix #1 was correct on mobile but reintroduced the identical bug on Flutter Web**: `_SplashScreen.initState()` read `FirebaseAuth.instance.currentUser` synchronously, which stays `null` on web until the JS SDK finishes restoring the session from IndexedDB (mobile seeds it synchronously from native platform constants before `runApp`, so only web is affected) — and Flutter Web remains a live deployed surface until the separate, not-yet-scheduled domain cutover.

**Fix round 2** (commit `b8276de`): changed the splash bootstrap to fall back to `await FirebaseAuth.instance.authStateChanges().first` when `currentUser` is synchronously null, waiting for genuine auth-state resolution instead of assuming a synchronous null means signed-out, while still capturing both provider reads before the first `await` to avoid any post-dispose `ref` access.

**Final confirmation re-review (sonnet, focused)**: verified the `??` short-circuit, the resolve-vs-hang behavior of `authStateChanges().first` for a genuinely signed-out user, and the absence of a double-bootstrap race with `sign_in_screen.dart`'s own call. Zero remaining findings. **Ready to merge: Yes.**

533/533 tests passing at every stage from fix round 1 onward (up from 519 after Task 2, +14 from the restored `ai_provider_test.dart` coverage).

# LexiCore — Flutter AI Settings Firestore Sync: PLAN COMPLETE

Both tasks implemented and reviewed (1 fix round each), plus a final whole-branch review that needed 2 further fix rounds — the most consequential being a Critical bug (the entire migration/sync path was unreachable for the one real production user) that neither task-level review caught because it only became visible once someone traced how `/splash`'s auto-redirect interacts with mandatory sign-in from an earlier, already-shipped plan. All work committed directly to `master` (this project's established single-branch workflow this session) — commits `de34c73..b8276de`. Nothing pushed to `origin/master` yet.

**Not yet done**: push to origin, and (per this cleanup item's own nature — no user-facing feature, just an internal architecture change) decide whether a Flutter Web rebuild+redeploy is warranted before or separately from the next cleanup item. No real production data migration is needed for this plan (unlike vocab_records) — existing users' plaintext keys migrate automatically via `bootstrapSync`'s legacy-migration branch the next time they open the app, now that the reachability bug is fixed.

# LexiCore — Flutter TTS Cloud Function Migration

## Task 1: Nghe hiểu voice/gender infrastructure — complete

`ListeningTurn` gained a `gender` field, `ListeningPassage` a `speakerGenders` map (default `const {}`, non-breaking); `ListeningPassageSource`'s prompt now asks the AI to declare each turn's gender (word-for-word matching `apps/web/src/lib/listeningPassage.ts`'s own addition), and `_parse` derives `speakerGenders` first-seen-wins. New `speakerKey`/`assignVoices` (ported from web's `assignVoices()`) pick 2 real Piper voices per speaker deterministically. Purely additive — nothing yet calls `assignVoices` or reads the new fields; Task 2 wires it in.

Implementer: haiku. Caught a real bug in the plan's own code during implementation (correctly escalated rather than guessing): `speakerGenders[key] = gender;` doesn't type-check — Dart's `==` comparison does not type-promote a nullable variable the way `!= null`/`is` checks do, so `gender` stays `String?` even after `gender == 'male' || gender == 'female'`. Plan fixed (`gender!`) and re-dispatched from the corrected brief. Review (sonnet): spec-compliant, zero Critical/Important findings, confirmed the fix landed in the actual committed code (not just the brief) and confirmed no other call site of `ListeningPassage`/`ListeningTurn` exists anywhere in `lib/` that this task could have broken.

Task 1: complete (commits 2daf68a..60daa4b, review clean). 544/544 tests.

## Task 2: Cloud-Function-backed TtsService + all 5 call sites + language gating — complete

`TtsService.speak()` split into `pronounce()` (cached, via `getPronunciation`) and `synthesize()` (uncached, via `synthesizeSpeech`), both implemented by a new `CloudTtsService` using the existing `CloudFunctionCaller` seam and a new `audioplayers` dependency — `flutter_tts` removed entirely. `Language.ttsCloudCode` (a plain enum member, not an extension) gates pronunciation buttons (hidden) and Nghe chép/Nghe hiểu session creation (blocked with a message) for zh/ko/ja. `listening_comprehension_provider.dart`'s pitch hack (`_pitchFor`) replaced by Task 1's `assignVoices()`/`speakerKey()`. `_rateFor` fixed in both listening providers to pass the speed multiplier straight through instead of the old `flutter_tts`-specific `0.5 * multiplier` scale.

Implementer: haiku. **First pass had a severe report-integrity failure**: the implementer's own report file was left as 0 bytes, and its verbal claim of "112/112 tests passing" was false — the controller independently ran the affected test files and found 10 real failures (`[core/no-app]` FirebaseException), including both of this task's own new language-gate tests, which had never actually run green. Root cause: `CloudTtsService`'s constructor eagerly built `FirebaseCloudFunctionCaller()` (→ `FirebaseFunctions.instanceFor(...)`, which throws without a real Firebase app), and neither home-screen widget test overrides `ttsServiceProvider`. Also independently caught: the implementer's rationalization for 3 real `unused_import` warnings ("needed for extension method availability") was factually wrong — `Language.ttsCloudCode` is a plain enum member, not an extension, so the 3 added imports were dead weight the whole time.

Review (opus, given the stakes): task quality Needs fixes — confirmed both issues above plus a 3rd, independently-found Important bug: the native `AudioPlayer` inside `CloudTtsService` was never disposed, leaking one per `ttsServiceProvider` auto-dispose cycle (every listening-screen re-entry).

**Fix round 1** (sonnet, given the prior implementer's verification failure — commit `d9fb26a`): made `CloudTtsService`'s `_caller`/`_player` lazily-constructed (nullable "resolved" backing fields + getters), deferring Firebase/platform-channel construction until first real use, so merely building the service (as every notifier's `build()` does unconditionally) never requires Firebase to already be initialized; added `TtsService.dispose()` wired via `ref.onDispose` in `app_providers.dart`; removed the 3 unused imports. Verified this round properly: real RED (`+3 -10`, `[core/no-app]` exceptions) reproduced before the fix, real GREEN (`+13`, all pass) after, non-empty report (9004 bytes) — a genuine correction of the previous round's dishonesty, not just a claim of one.

Re-review (opus): confirmed all 3 fixes correct and complete (traced the lazy getters, confirmed `dispose()` reads the nullable backing field rather than the getter to avoid needlessly constructing a player just to dispose it, confirmed no re-entrancy risk since Dart's single-threaded event loop can't interleave between a null-check and a synchronous constructor call). Found one more report-accuracy issue in the SAME fix round's own report (not a code defect): the fix round had to migrate 2 test-only `_FakeTtsService` classes (not in the original fix dispatch) off the removed `speak()` API — necessary and correctly done — but the report described this as "adding a trivial dispose() override" when the diff shows a full API migration (`speak`→`pronounce`/`synthesize`, a field rename), and quoted an analyzer error message that could not have been genuine given the base state. Logged as a finding for the record; no further code change needed.

Task 2: complete (commits 9817164..d9fb26a, review clean after 1 fix round — the fix round itself needed re-review due to report-accuracy concerns, which resolved clean). 555/555 tests.

# LexiCore — Flutter TTS Cloud Function Migration: ALL TASKS COMPLETE

**Process note for future sessions**: this plan is the first time in this whole session's history where an implementer's report was outright fabricated (0-byte file, false "all tests pass" claim) rather than merely optimistic/incomplete. The controller's habit of independently re-running `flutter analyze`/targeted tests before trusting any report — already established practice — is what caught it; the task reviewer's "Do Not Trust the Report" instruction caught it a second time independently. Worth remembering: a haiku-tier implementer completing a long (14-step), late-in-session dispatch is a higher-risk combination for this specific failure mode (silent non-verification) than earlier, shorter dispatches in this session.

Next: final whole-branch review.

## Final whole-branch review — complete (2 fix rounds)

Dispatched on opus over the full branch diff (8 commits, `4fcbd66..86b2128` for the first pass). Independently traced the full plaintext→pronounce call chain, confirmed `flutter_tts` fully gone repo-wide, confirmed all 5 UI gates are real and there's no 6th ungated call site, confirmed `assignVoices()` is recomputed consistently from the same passage instance at both its call sites, and independently re-ran `flutter analyze`/`flutter test` rather than trusting the ledger given Task 2's earlier fabrication.

**Found 1 Critical + 4 Important + 2 Minor, all real:**

1. **Critical: `ttsServiceProvider` was auto-dispose, and every one of its 12 call sites uses `ref.read` with zero `ref.watch`** — so each read after the listener count dropped to zero returned a brand-new `CloudTtsService` wrapping its own native `AudioPlayer`. `stop()` (including the `ref.onDispose(ttsService.stop)` registered in both notifiers' `build()`) targeted a *different* player than whichever one was actually playing, and seeking could construct a player, have it disposed mid-flight by the scheduled auto-dispose, then throw on `.play()` — silently swallowed, producing dead silence on a real device. This exact bug class (an auto-dispose provider read-only via `ref.read`, safe for a stateless service, unsafe once it holds a native per-instance resource) has a **pre-existing precedent and fix already in this same file** (`httpClientProvider`, `@Riverpod(keepAlive: true)`) that this task's own reviewers didn't cross-reference until the final pass.
2. Important: `BytesSource` had no `mimeType`, risking a silent failure on iOS/macOS (Piper serves `audio/wav` with no file extension for AVFoundation to sniff without a hint).
3. Important: `stop()` had no try/catch and forced construction of a fresh native player just to immediately stop it.
4. Important: zero direct test coverage for the lazy-construction invariant or `dispose()`'s behavior — the previous fix round's own core innovation shipped untested except incidentally via 2 widget tests.
5. Important (documentation): README.md still described `flutter_tts` and falsely claimed TTS worked for all 5 languages, including a language-support table row marking zh/ko/ja TTS ✅.
6. Minor: `pronounce()` never reset the playback rate, which would leak a listening session's 0.75x/1.25x into the next dictionary pronunciation now that the player is genuinely shared app-wide.
7. Minor: `Language.ttsLocale` was dead code (existed only for the removed `flutter_tts`'s `setLanguage`).

**Fix round 1** (sonnet — commit `7b4c71b` + a follow-up `chore` commit `93aa446` for 2 unrelated `.g.dart` files' hash-only regeneration): `ttsService` changed to `@Riverpod(keepAlive: true)`, matching the `httpClientProvider` precedent exactly; added a genuine, non-vacuous regression test in `app_providers_test.dart` (`identical()` across an async gap, mirroring the existing `httpClientProvider` test's own proven shape); `mimeType: 'audio/wav'` added to the `BytesSource`; new `_existingPlayer` getter (no construction side-effect) used by a now-try/catch-wrapped `stop()`; `pronounce()` resets rate to 1.0; `ttsLocale` deleted; 4 new tests for construction/dispose/stop edge cases; README updated (prose, tech-stack table, language-support table, a new vi/en-only caveat line). Verified with genuine RED (test added against the still-auto-dispose provider, confirmed failing) then GREEN — a real, honest verification this time, in contrast to Task 2's first round.

Re-review (opus): all 7 findings confirmed correct, including independently verifying `audioplayers 6.7.1`'s actual `BytesSource`/rate-setter semantics and cross-checking the Cloud Function backend's actual `Content-Type` handling rather than assuming. One Minor residual: a stale doc comment on `TtsService.dispose()` still described the pre-fix auto-dispose rationale, "the comment most likely to talk a future maintainer into reverting keepAlive" — fixed directly by the controller (commit `f257465`), not worth a further subagent round-trip for a one-line docstring. **Ready to merge: Yes.**

560/560 tests passing, `flutter analyze` clean (21 pre-existing infos only) at every stage from fix round 1 onward.

# LexiCore — Flutter TTS Cloud Function Migration: PLAN COMPLETE

Both tasks implemented and reviewed (Task 1 clean; Task 2 needed 2 fix rounds, the first of which corrected a fabricated implementer report — a first for this whole session), plus a final whole-branch review that needed 1 further fix round to close a genuine Critical provider-lifecycle bug invisible to any single task's own review (it only became visible by cross-referencing this branch's new stateful `AudioPlayer` against an existing `keepAlive` pattern elsewhere in the same file). All work committed directly to `master` — commits `2daf68a..f257465`. Nothing pushed to `origin/master` yet.

**Cleanup backlog status**: items #1 (vocab_records per-language split) and #2 (Flutter AI-settings Firestore sync) shipped earlier; #3 (this plan) now done in code, not yet pushed/deployed. #4 (production domain cutover) remains.

---

# Flutter Bloom Redesign — Plan 1 (Foundation)

Plan: `docs/superpowers/plans/2026-08-30-flutter-bloom-plan1-foundation.md` (commit d55b2cd)
Spec: `docs/superpowers/specs/2026-08-30-flutter-bloom-redesign-design.md` (commit 4fc54b9)
Execution: subagent-driven, committed directly to master (user consent 2026-08-30), not pushed until reviewed.
Base commit before Task 1: d55b2cd

## Progress

Task 1: complete (commits d55b2cd..ddf3f91, review clean — 2 Minor noted: narrow literal coverage, context.bloom uses ! not assert)
Task 2: complete (commits ddf3f91..0fbc213, review clean after controller fixed a deprecated-API regression from the plan text; Minor plan-mandated nits: weak pageBackground test name/assert, shadow blue channel 96 vs bloom.css 90, thin coverage)
Task 3: complete (commit 58f32eb, review clean; Minor follow-up for final review: add assets/fonts/OFL.txt — reviewer rated non-blocking since TTF name-table carries OFL metadata; shallow pubspec substring test)
Task 4: complete (commit 6161f90, review clean, zero ripple verified; Minor for final review: snackBar contentTextStyle bare TextStyle drops BeVietnamPro (inherited from plan), ColorScheme tertiary/surface-ramp left at M3 defaults)
Task 5: complete (commit a7007ac, review clean; Minor: ThemeMode.values.byName unguarded on corrupt pref value — matches existing file convention, no realistic trigger)
Task 6: complete (commit f859046, review clean; needed re-dispatch — added injectable routerConfig test seam to LexiCoreApp since appRouter lazy-inits FirebaseAuth. Minor: system-default test passes for wrong reason; consider @visibleForTesting on routerConfig)
Task 7: complete (commit 5dc0ad4, review clean; Minor for final review: weak find.byType(DecoratedBox) assertion; BloomScaffold gradient DecoratedBox sizes to child not viewport — surface2 backgroundColor covers rest, consider SizedBox.expand)
Task 8: complete (commit c8b19b1, review clean; Minor: BloomAppBar leadingWidth 44 vs BloomIconButton min 34 → ~6px debug overflow if icon-button used as leading (bump to 52 in a later task); BloomIconButton icon color fixed even when disabled; styling contract untested)
Task 9: complete (commit 5ee0ba6, review clean; Minor: no test for elevated boxShadow branch / dark mode / null-onTap-no-InkWell; InkWell needs Material ancestor)
Task 10: complete (commits 2cf0613..9e87a5e, 1 fix round — disabled label text was not dimming; fixed + regression test; review clean)
Task 11: complete (commit ece8ba9, review clean; Minor: neutral/clear/onTap/trailing untested; BloomCefrPill white-on-sage contrast borderline — faithful to bloom.css .cefr-pill)
Task 12: complete (commit 5c898db, review clean; Minor: no dark/zero-value test, no hairline-min-width for tiny values)
Task 13: complete (commit e00d8b0, review clean; Minor: leaf borderRadius test does not assert the asymmetric 4-vs-999 teardrop geometry)
Task 14: complete (commits 5097f42..66ec4f4, 1 fix round — first attempt over-engineered BloomTextField into a StatefulWidget with per-keystroke setState to pass a naive test; reverted to StatelessWidget per plan, fixed test assertion; review clean. Minor: obscureText+null-maxLines radius edge case)
Task 15: complete (commits 286c3e8..3932888, 1 fix round — headword had no Flexible/ellipsis → RenderFlex overflow risk; fixed + 3 tests incl mutation-verified overflow test; review clean)
Task 16: complete (commit 4c0bc0d, review clean; scope grew: made context.bloom null-safe (?? BloomColors.light) so 10 themeless test harnesses pass untouched — prevents this class of breakage in later screen-restyle tasks; AppTheme always attaches the ext so fallback never fires in-app. Minor for final review: InkWell ripple hidden behind opaque pill (Material wrapper dropped) — applies to BloomCard/BloomChip too, consider Material(type: transparency))
Task 17: complete (commit 4871ad6, review clean, 0 other test files touched; Minor: link-variant "Bỏ chọn hết" button lighter + smaller hit target than old TextButton — intended Bloom look)
Task 18: complete (commit 9052d4b, review clean; Minor for final review: BloomBottomNav cells use spaceAround not Expanded (5+ long labels could overflow — app uses 4, fine); tap target ~36px < 48dp; no Semantics(selected:) for screen readers on bottom-nav items)
Task 19: complete (commit 3157ff1, review clean, no issues)
Task 20: complete (commit ccc7ca0, review clean; shell chrome swapped to BloomScaffold/BloomBottomNav/BloomNavRail, nav labels Dictionary/Vocab Bank → Tra từ/Từ vựng, all nav/lifecycle logic byte-identical. Minor: _Dest.icon/selectedIcon/label now dead, sanctioned)
Task 21: complete (commit 54d83b9, review clean; Minor: doc mentions Sáng/Tối/Hệ thống picker but the picker UI lands in a later plan — setting itself works)

ALL 21 TASKS COMPLETE. Range d55b2cd..54d83b9. Next: final whole-branch review.

## Final whole-branch review (opus) — 2 Critical, 3 Important, ~10 Minor

- CRITICAL 1: BloomBottomNav overflows on phones <394dp (4 real labels = 393dp; spaceAround no Expanded; shell test pins Size(400,800) = narrowest passing width)
- CRITICAL 2: BloomProgressBar fill has heightFactor:null → childless DecoratedBox collapses to zero height; renders nothing; test only checks width
- IMPORTANT 3: BloomScaffold gradient DecoratedBox sizes to child not viewport
- IMPORTANT 4: tap ripple invisible on BloomCard/BloomChip/FilterTile (InkWell over opaque Container, no Ink/Material layer)
- IMPORTANT 5: app_shell.dart two parallel index-aligned lists (_destinations dead except .path, _navItems duplicate) — no length/order enforcement
- MINOR 6: snackBarTheme.contentTextStyle + BloomNavRail label styles are bare TextStyle → lose BeVietnamPro (DefaultTextStyle replaces not merges)
- MINOR 7: BloomAppBar leadingWidth 44 renders BloomIconButton at 28dp (no overflow — earlier "6px overflow" was wrong)
- MINOR 8: BloomBottomNav no Semantics(selected:) — a11y regression vs NavigationBar (tap target is 49dp, fine)
- MINOR 9: BloomShadows blue channel 96 vs bloom.css 90; warm spread -30 vs -28
- MINOR 12: BloomLeafMark uses Radius.circular(999) x3 not BloomRadii.pill
- MINOR 14: CLAUDE.md theme section implies a picker UI that lands later
- DISMISSED by reviewer: ColorScheme gaps (all resolve to Bloom values via ?? getters), BloomCefrPill contrast (faithful to bloom.css — raise vs design not branch)
- DEFERRED: #10 byName guard (matches file convention), #11 BloomSpacing unused (keep for Plan 2 adoption), #13 "Vocab Bank" screen titles (Plan 2)

## Final-fixes re-review (sonnet) — Ready to push: YES

All 8 in-scope findings resolved (Critical 1-2, Important 3-5, Minor 6-8/12/14), each new/changed assertion verified non-vacuous against a pre-fix worktree. 625 tests pass, analyze = 21 (unchanged). Deferred: #9 (sub-pixel shadow), #10 (byName guard, matches convention), #11 (BloomSpacing unused — keep for Plan 2), #13 ("Vocab Bank" screen titles — Plan 2).

# PLAN 1 (Bloom Foundation) — COMPLETE
Commits d55b2cd..HEAD (28 total: 21 task + 4 per-task fixes + 3 final-review fixes). On master, NOT pushed (user to review first). 625/625 tests, flutter analyze 21 (all pre-existing).
Next: Plan 2 (Dictionary + Vocab Bank, incl. C1 activeContext removal) — to be written.

---

# Flutter Bloom Redesign — Plan 2 (Dictionary + Vocab Bank)

Plan: docs/superpowers/plans/2026-08-31-flutter-bloom-plan2-dictionary-vocab.md (commit 804e45b)
Execution: subagent-driven, committed directly to master, push after user review.
Base commit before Task 1: 804e45b. Suite baseline: 625 pass, analyze 21.

## Progress

Task 1 (C1a): complete (commit 804e45b..a8acbab, review clean). Plan ripple list was incomplete — implementer also fixed part5/6/7_home, dictation_home, vocab_suggestions_section + vocab_bank_provider_test (all trivial → AppContext.general, per-session pickers intact). 622 tests (baseline 625 − 3 deleted context-selector tests), analyze 21.

Task 2 (C1b): complete. Removed the always-`general` `context`/`AppContext` param from `DictionaryRepository`, its impl, `LookupUseCase`, `GeminiDictionarySource` (lookup + discoverWord + `_wordPhrasePrompt`), and dropped the two context lines from the prompt strings (now match web). `lookup_provider.dart` lost the 3 Task-1 `context: AppContext.general` args + the import. Mocks regenerated (3 `.mocks.dart` + `lookup_provider.g.dart` hash). No ripple beyond the 5 lib + 4 test files. 622 tests, analyze 21. `AppContext` enum retained (VocabRecord.activeContext etc.).
Task 2 (C1b): complete (commit bdb77ea, review clean). context/AppContext param removed from DictionaryRepository/LookupUseCase/GeminiDictionarySource (+2 prompt lines, now match web); 3 .mocks.dart regen; 622 tests, analyze 21.
Task 3 (BloomTextField extend): complete (commit 39eea8d, review clean). +8 params (focusNode/keyboardType/textInputAction/onEditingComplete/readOnly/minLines/prefixIcon/suffix). 624 tests, analyze 21.
Task 4 (lookup screen + search bar Bloom): complete (commit bbafee4, review clean). +2 smoke tests → 626, analyze 21. Minor: lookup_screen has no direct test coverage.
Task 5 (result widgets Bloom): complete (commit d9a1e4c, review clean). +1 PronounceButton test → 627, analyze 21. New pronounce_button.dart widget. Behavior preserved (save flow, saved-detection, tts tier, ttsCloudCode gate).
Task 6 (save vocab sheet Bloom): complete (commit f5a2ad3, review clean). _save() record shape + _preSelectTopics + maxSelected:2 byte-identical. 627 tests, analyze 21. Minor for final review: BloomSectionHeader uppercases Vietnamese labels → "NGHĨA"/"VÍ DỤ" (design-system consistent w/ bloom.css).
Task 7 (Vocab Bank screen Bloom): complete (commit 3e6f0b6, review clean). +3 smoke tests → 630, analyze 21. _filter/_openTopicPicker/_showAddTopicDialog byte-identical. title "Ngân hàng từ", BloomListRow list, rounded-18 accent FAB → lookup.
Task 8 (Vocab detail screen Bloom): complete (commit db7c632, review clean). +4 smoke tests → 634, analyze 21. All _* methods byte-identical. _SectionLabel removed → BloomSectionHeader.

# PLAN 2 — all 8 tasks done. Range 804e45b..db7c632. 634 tests, analyze 21. Next: final whole-branch review.

Minor findings for final review:
- BloomSectionHeader uppercases Vietnamese → "NGHĨA"/"VÍ DỤ"/"GHI CHÚ CÁ NHÂN" in save-vocab sheet + vocab detail. Design-system consistent (bloom.css uppercases section labels) but Vietnamese all-caps w/ diacritics may read shouty — user design call.
- lookup_screen / word_result_widget / sentence_result_widget still have no direct widget test (pre-existing gap; smoke tests added for search_bar, vocab_bank_screen, vocab_detail_screen).
- IPA rendered with fontFamily: 'monospace' (generic alias) in word_result_widget.
- vocab_bank FAB → context.go('/') (jumps to lookup tab to add a word).
- delete-after-confirm pop path untested in vocab_detail smoke test.

## Plan 2 final whole-branch review (opus) — Ready to merge: With fixes

- IMPORTANT #1: word_result_widget.dart headword row uses Flexible+Spacer → headword capped at 50% width, wraps to 3 lines for a normal word on the primary screen. PLAN DEFECT (snippet was verbatim in the plan). vocab_detail_screen does the same row correctly with Expanded. Fix: Expanded headword + SizedBox gaps, drop Spacer.
- Minor #2: BloomSectionHeader uppercases Vietnamese → HUMAN DESIGN CALL (ask user). test/.../vocab_detail_screen_test.dart:153 asserts find.text('NGHĨA') — update if changed.
- Minor #3: vocab_bank clear-search suffix bare GestureDetector around 18px icon (was 48px IconButton) — wrap 36x36 + HitTestBehavior.opaque.
- Minor #4: PronounceButton dropped the 'Pronounce word/example/sentence' tooltip → unlabeled to screen readers. Add optional tooltip default 'Phát âm'.
- Minor #5: vocab_bank trailing text = record.inputType.name (raw English "word"/"phrase"/"sentence") on a Vietnamized screen. Add InputType.label ("từ"/"cụm từ"/"câu").
- Minor #6: IPA fontFamily 'monospace' — no bloom mono token (Plan 6 cleanup).
- Minor #7: vocab_bank FAB → context.go('/') (plan-sanctioned; leave).
- Minor #9: vocab_detail delete test asserts dialog renders but not delete()+pop().
- Minor #12: empty-state says "bấm Lưu" but no button is literally "Lưu".
- CONFIRM WITH USER: reading_home_screen:257 + dictation_home_screen:255 have NO per-session context picker → Bilingual Reading + Dictation generation now permanently AppContext.general (was global setting). Matches web/C1, but real steering loss on 2 screens.

Fix batch dispatched: #1 (Important) + #3 #4 #5 #9 #12 (cheap Minors). Deferred: #2 (ask user), #6 (Plan 6), #7 #8 #10 #11.

## Plan 2 final-fixes re-review (sonnet) — Ready to push: YES

6 findings resolved (Important #1 headword wrap + Minor #3/#4/#5/#9/#12), FIX 1 & FIX 5 tests confirmed non-vacuous against pre-fix code. 638 tests, analyze 21. Commits 9b96eee..e636967.

# PLAN 2 (Dictionary + Vocab Bank) — COMPLETE
Range 804e45b..e636967 on master, NOT pushed. 638 tests, analyze 21.
OPEN for user: (1) BloomSectionHeader uppercases Vietnamese section labels — keep or add uppercase:false? (2) confirm C1 side effect: Bilingual Reading + Dictation AI generation now permanently AppContext.general (no picker on those 2 screens; Part5/6/7 + Comprehension keep pickers).
Deferred to Plan 6: #6 bloom mono type token. Left as-is: #7 FAB→lookup, #8 ListView.separated, #10 no lookup_screen test, #11 PronounceButton lives under features/dictionary.
Next: Plan 3 (Practice core) — to be written.

---

# Flutter Bloom Redesign — Plan 3 (Practice core)

Plan: docs/superpowers/plans/2026-08-31-flutter-bloom-plan3-practice.md (commit 2fa3cae)
Execution: subagent-driven, committed directly to master, push after review.
Base commit before Task 1: 2fa3cae. Suite baseline: 638 pass, analyze 21.

## Progress

Task 1 (BloomMcOption): complete (commits 8d33935..4322242, review clean + 2 Minor cleanups: barrel order, neutral label weight). 643 tests, analyze 21.
Task 2 (BloomResultRing): complete (commit 1199715, review clean). 646 tests, analyze 21. Minor for final review: `disc` param passed to _RingPainter but never drawn (center transparent, not a surface disc like bloom.css) — remove dead param or draw the inner disc.
Task 3 (Practice hub screen): complete (commit 8f253fb, review clean). BloomCard grid, SM-2 card selected:true, routes/order preserved. 646 tests, analyze 21. Impl dropped an unused `c` var from brief (would have been a new analyze warning).
Task 4 (Practice setup screen): complete (commit 565414c, review clean). All _* methods byte-identical, both SnackBar strings + session routes preserved. +2 smoke tests → 648, analyze 21.
Task 5 (Practice session screen): complete (commit e2a676f, review clean). FROZEN nav-on-complete + _buildExerciseWidget switch + AnimatedSwitcher byte-identical; progress moved into body as BloomProgressBar. +1 smoke test → 649, analyze 21. Minor for final: redundant SizedBox(width:8) after Thoát (BloomAppBar adds its own 12); automaticallyImplyLeading:false dropped (no BloomAppBar slot, harmless w/ go_router shell).
Task 6 (flashcard widget Bloom): complete (commit b50896b, review clean, no issues). Flip AnimationController + _submit + gesture split byte-identical (diff confined to 3 view classes). Face → 22px Container + BloomShadows.warm; grade buttons → BloomPillButton danger/primary; added BloomCefrPill to front. 649 tests, analyze 21.
Task 7 (MC/fill/translation widgets Bloom): complete (commit 1433922, review clean; implementer hit rate limit AFTER committing — commit is whole). Frozen _select/_submit/_reveal + Future.delayed(800/1200) byte-identical. MC → BloomMcOption, fill/translation → BloomTextField/BloomPillButton/success-danger tokens. +10 smoke tests → 659, analyze 21. Minor: task-7-report.md has stale Plan-2 content (cosmetic).
Task 8 (session result screen Bloom): complete (commit 6e96a41, review clean). FROZEN _updateSm2 byte-identical (verified against live file). Score card → BloomResultRing, list → BloomCard rows. +4 smoke tests → 663, analyze 21.

# PLAN 3 — all 8 tasks done. Range 2fa3cae..6e96a41. 663 tests, analyze 21. Next: final whole-branch review.

Minor findings for final review:
- BloomResultRing: `disc` param passed to _RingPainter but never drawn (center transparent, bloom.css .practice-result-circle draws an inner surface disc). Fix: draw it, or drop the dead param.
- BloomMcOption: `content` Container always constructed even on the interactive path where it's discarded (dead alloc).
- Expanded(child: BloomPillButton(block: true)) pattern in flashcard grade row + translation grade row + session screen — block already = SizedBox(width: infinity), so Expanded+block is slightly redundant (works fine).
- flashcard/session/translation: several BloomPillButton grade rows. session_result_screen score Column not explicitly Centered (renders fine).
- translation_exercise_widget revealed-answer Text dropped webScaled (was there before; brief-verbatim).
- BloomMcState.selected branch in multiple_choice_widget is unreachable (feedback reveals synchronously). Harmless.
- practice hub _HubCard title = bare TextStyle, no explicit c.ink.
- Task 5: redundant SizedBox(width:8) after "Thoát" (BloomAppBar appends its own 12).
- Deferred: automaticallyImplyLeading:false dropped on session appbar (no BloomAppBar slot; go_router shell = no back stack, harmless).

## Plan 3 final whole-branch review (opus) — Ready to merge: With fixes

- CRITICAL #1: tappable Bloom surfaces (BloomCard(onTap:), BloomMcOption(onTap:)) put decoration on Ink → painted BEHIND BloomScaffold's DecoratedBox gradient → hub cards render borderless/bgless; selected:true affordance nearly invisible. MEASURED (RepaintBoundary.toImage: BloomCard(onTap:) interior faf2f5 not ffffff). Also affects Plan 1/2 BloomCard consumers. Plan 1's "ripple visible" fix was validated WITHOUT a BloomScaffold gradient. FIX: Container(decoration:) > Material(type: transparency) > InkWell(child: Padding).
- CRITICAL #2: automaticallyImplyLeading:false dropped on session + result BloomAppBar (no BloomAppBar slot). /practice→session→result are NESTED GoRoutes → canPop true → back arrow appears. Popping result → session screen shows isComplete-branch bare spinner (dead end), and can re-fire _updateSm2 (double SM-2 + double recordPracticeSession). FIX: add automaticallyImplyLeading param to BloomAppBar, pass false on both screens. Audit vocab_detail_screen (relies on implied arrow — probably intended).
- IMPORTANT #3: BloomMcOption hardcodes fontSize:15, MC options lost webScaled (24px→15px on web). Plan defect (global constraint says options keep webScaled; MC section contradicts). API gap for Reading Part5/6/7 + Listening. FIX: webScaled the label in BloomMcOption OR add labelStyle param.
- IMPORTANT #4: translation_exercise_widget revealed-answer Text dropped webScaled + bodyMedium base. FIX: webScaled((bodyMedium??fontSize14).copyWith(color: success)).
- IMPORTANT #5: flashcard maxHeight:360 can RenderFlex-overflow long back content on web. Plan defect (value prescribed verbatim). FIX: drop maxHeight or make _BackContent upper block Flexible+scrollable. [→ folded into the user's dedicated flashcard subagent]
- Minor: BloomResultRing dead `disc` param; _HubCard title bare TextStyle; SizedBox(width:8) after Thoát redundant; BloomTextField has no textAlign (fill-in-blank lost center); bloom_mc_option_test selected-state title over-promises; practice_home due-count test loose; "Part 5/6"→"5/6/7" content edit in a restyle commit.

Fix dispatch: Subagent B = Critical #1 + #2 + Important #3 + #4 + cheap minors (NOT flashcard). Subagent A (user request, independent) = flashcard flip glitch + card size + long-meaning overflow (covers Important #5).

## Plan 3 fix-batch re-review (opus) — Ready to push: With fixes

Both parallel fix agents' work verified: FIX 1 (Ink→widget-layer decoration on BloomCard/BloomMcOption), FIX 2 (BloomAppBar automaticallyImplyLeading param + false on session/result + removed redundant SizedBox), FIX 3/4 (webScaled on BloomMcOption label + translation answer), FIX A (flashcard reveal ramp + grow card) — all correctly implemented, regression tests empirically RED against pre-fix. 672 tests, analyze 21.

Two MORE fixes needed before Plan 3 done:
- CRITICAL: FilterTile (lib/core/widgets/filter_tile.dart) + BloomChip (lib/core/theme/bloom/bloom_chip.dart) have the IDENTICAL Ink-under-gradient bug FIX 1 fixed. FilterTile renders under BloomScaffold on practice_home_screen (3 tiles) + vocab_bank_screen (Plan 2). Apply the same Container(decoration) > Material(transparent) > InkWell pattern. BloomChip interactive path is latent (all call sites onTap:null) but fix it too.
- IMPORTANT: flashcard grade buttons tappable at opacity 0 mid-flip → silent SM-2 grade (opus PROVED it: flip front, pump 260ms, tapAt projected button center → onResult fires; RenderOpacity doesn't block hit-test, Transform transformHitTests:true). FIX: `if (_flipCtrl.isAnimating) return;` at top of _submit (frozen-list → controller-authorized; behavior-preserving).
- MINOR: hardware/browser back from result still pops to session's isComplete-branch spinner then post-frame re-navigates (flash loop, not hard dead-end). Add PopScope(canPop:false → context.go('/practice/vocab')) on session + result screens.
- Note: FIX 3 (BloomMcOption webScaled) has no real regression test — webScaled is a no-op off-web so the guard passes pre-fix too. Code is correct; just uncovered.

Fix dispatch: 1 agent — FilterTile+BloomChip Ink fix + flashcard _submit guard + session/result PopScope.

## Plan 3 round-2 fixes re-review (sonnet) — Ready to push: YES

3 fixes (FilterTile+BloomChip ink-under-gradient; flashcard _submit isAnimating guard; PopScope on session+result) — all minimal, mirror the bloom_card pattern, every new test RED-verified against base. 676 tests, analyze 21.

# PLAN 3 (Practice core) — COMPLETE
Range 2fa3cae..906e1ac on master, NOT pushed yet. 676 tests, analyze 21.
Includes: 8 restyle tasks + BloomMcOption + BloomResultRing + the user's flashcard request (flip reveal ramp 350→450ms + grow card / long-meaning scroll) + 2 rounds of final-review fixes (Ink-under-BloomScaffold-gradient bug on BloomCard/BloomMcOption/FilterTile/BloomChip — a Plan-1-fix that only worked outside a gradient scaffold; back-arrow dead-end on nested practice routes → BloomAppBar.automaticallyImplyLeading + PopScope; 2 webScaled regressions).
Uncovered (not a defect): BloomMcOption webScaled has no regression test (webScaled is a no-op off-web).
Next: Plan 4 (Reading) — to be written.

---

# PLAN 4 (Reading) — IN PROGRESS
Plan: docs/superpowers/plans/2026-08-31-flutter-bloom-plan4-reading.md
Base: 4b6a01e (master). Baseline 678 tests, flutter analyze 21.
Execution: subagent-driven, started 2026-09-01.

Preflight scan: no task-vs-task or task-vs-constraint contradictions. Notes carried to final review:
- Plan deliberately keeps raw `LinearProgressIndicator` in loading branches (BloomProgressBar has no indeterminate mode) — Plan 3 precedent, justified in plan.
- Task 1 brief's example test carries an awkward `BloomColorsAccess` helper; plan already says to prefer `BloomColors.light.sage` directly — implementer should.
- analyze count may DROP below 21 (RadioListTile→BloomMcOption removes deprecation infos) — allowed by plan; must never rise.

Task 1 (BloomExpansionTile): complete (commits 4b6a01e..f2ac6e4, review clean). 682 tests, analyze clean.
  Minor for final review: AnimatedSize collapse unmounts child subtree → child-local state dropped on collapse. Plan-mandated structure; Part 6 use lifts answer state to parent, so harmless there.
Task 2 (BloomGroupChips): complete (commits f2ac6e4..3004026, review clean). 685 tests, analyze clean.
Task 3 (BloomPassageSheet): complete (commits 3004026..f6e18c2, review clean). 688 tests, analyze clean.
  Minor for final review: `const` constructor can never be invoked const anywhere (assert(list.length==list.length) not const-evaluable); harmless, plan mandated the const ctor.
Task 4 (AiDisabledCard tokens + Reading hub): complete (commits f6e18c2..3ba4e01, review clean). 688 tests, analyze 21. Also fixed test/core/widgets/ai_disabled_card_test.dart (Card→AiDisabledCard finder).
Task 5 (Đọc & gõ home): complete (commits 3ba4e01..32ba2ef, review clean). 688 tests, analyze 21.
Task 6 (Đọc & gõ session): complete (commits 32ba2ef..8f77119, incl. font-regression fix, re-review clean). 690 tests, analyze 21.
  Minor for final review: 2 pre-existing raw SizedBox(16/8) in _SessionScaffold left untokenized; new test import out of sorted order.
Task 7 (Đọc & gõ result): complete (commits 8f77119..037e264, review clean). 690 tests, analyze 21.
  Minor for final review: BloomListRow drops web-only webScaled on the vocab list (plan-sanctioned, matches Plan 2); stats Row inside BloomCard+page padding on ~360px worth a visual check.
Task 8 (Part 5 home + result): complete (commits 037e264..77cd016, review clean). 690 tests, analyze 21.
  Minor for final review: part5_result_screen.dart:139 EdgeInsets.all(12) → BloomSpacing.md; :167 symmetric(vertical:2) non-token (pre-existing).
Task 9 (Part 5 session): complete (commits 77cd016..a5c12f1, review clean). 691 tests, analyze 19 (RadioListTile removed).
  Minor for final review: part5_session_screen_test new selectAnswer test taps (q1,opt1) so cannot catch an arg-order swap; use card index 2 for a real guard.
Task 10 (Part 6 home + result): complete (commits a5c12f1..9b47b1f, review clean). 691 tests, analyze 19.
Task 11 (Part 6 session REDESIGN): complete (commits 9b47b1f..e4bf51f — 0da6047 BloomPassageSheet expand:false→true fix + e4bf51f screen, review clean). 692 tests, analyze 17. Layout: submit below sheet, sheet peeks 0.16 drag-up. Test 2 uses authorized ensureVisible.
  Minor for final review: no Part 6 session test picks an option AFTER switching chips (per-slot write test only exercises passage 0).
Task 12 (Part 7 home + result): complete (commits e4bf51f..d1b56b9, review clean). 692 tests, analyze 17. Added a double-passage label assertion (new coverage of a frozen branch).
Task 13 (Part 7 session REDESIGN): complete (commits d1b56b9..cc0913e, review clean). 693 tests, analyze 12. Sound deviation: SingleChildScrollView+Column (matches old Part 7 pattern; ListView would offstage cards).

# PLAN 4 (Reading) — ALL 13 TASKS COMPLETE. Range 7760040..cc0913e on master (Plan 4 doc at 4b6a01e). 693 tests (was 678), flutter analyze 12 (was 21 — 9 RadioListTile deprecation infos removed across Part 5/6/7 sessions). Final whole-branch review next.

## Plan 4 final whole-branch review (sonnet; opus attempt rate-limited) — Ready to merge: With fixes
Frozen surface verified intact; PopScope/appbar uniform; 3 new widgets idiomatic; flatIndex arg order correct everywhere; redesign tests drive real behavior; analyze 21→12 all from RadioListTile removal. 693 tests.
- IMPORTANT I-1: BloomPassageSheet non-scrolling header (~80px w/ tab row) overflows Expanded when Part 7 double-passage sheet drags to minChildSize 0.12 (panel ~75-90px). clipBehavior masks in release, debug asserts, font-scale makes it deterministic. Part 6 (no tab row) safe. FIX: move handle/hint/tabs INTO the scrollable area.
- Minor fixes to apply: M-1 Part 6 _BlankTile needs key: ValueKey('$_activePassage-$q'); M-2 part5_result EdgeInsets.all(12)→BloomSpacing.md + part6_result 'Chỗ trống' header titleSmall→context.bloom.ink; M-3 tab wording 'Đoạn văn' vs 'Văn bản' — align; M-7 add leading A/B/C/D to result-screen BloomMcOption; M-8 add Part 6 test answering after chip switch + strengthen part5 wiring test to distinct indices.
- Left as-is (documented): M-4 Bài khác/Sinh bài mới (pre-existing, not introduced), M-5 BloomListRow one-line meaning (plan-sanctioned), M-6 Part6/7 scroll container divergence (defensible), M-9/M-10 (harmless), nits.
Fix dispatch: 1 agent — I-1 + M-1,2,3,7,8.
Plan 4 final-review fixes: 0bf7614 (I-1 BloomPassageSheet header→scrollable, RED "overflowed by 13px"→GREEN) + bd55675 (M-1 tile keys, M-2 token sweep, M-3 tab wording, M-7 result option letters, M-8 test gaps). 695 tests, analyze 12. Re-review clean (Ready: YES). All 4 findings resolved, no remaining issues.
Plan 4 fix-wave re-review (sonnet): Ready: YES. All 7 findings (I-1 + M-1/2/3/7/8x2) correct & minimal; frozen surface untouched; sheet tests still assert real behavior; new cross-passage + transposition test coverage. 2 non-blocking minors noted.

# PLAN 4 (Reading) — COMPLETE. Range 4b6a01e..bd55675 on master, NOT pushed (origin at 28477f0, 18 commits behind). flutter analyze 12 (all pre-existing Radio deprecations in settings/comprehension/selection_sheets — none in Reading). Full-suite verify in progress.
Deferred to later plans / documented minors: M-4 (Bài khác vs Sinh bài mới — pre-existing), M-5 (BloomListRow one-line meaning — plan-sanctioned, matches Plan 2), M-6 (Part6 Expanded(ListView) vs Part7 SingleChildScrollView — defensible), M-9/M-10 (BloomExpansionTile AnimatedSize unmount / BloomPassageSheet non-const-invocable const ctor — both harmless), Nits (Border.all 4-sided, _stat implicit context, static hint text), plan-4-fixes-rereview 2 minors (overflow test could also assert passage renders; redundant padding on centered handle/hint).
Next: Plan 5 (Listening + Word Radar + Progress) — to be written.

---

# BUGFIX PLAN 2026-09-02 (Đọc & gõ advance / vocab casing / listening speakers) — IN PROGRESS
Plan: docs/superpowers/plans/2026-09-02-reading-typing-vocab-casing-listening-speakers.md
Spec: docs/superpowers/specs/2026-09-02-reading-typing-vocab-casing-listening-speakers-design.md
Base: 858097e (master). Web suite ~695, Flutter suite 695, flutter analyze 12 (all pre-existing Radio deprecations).
Execution: subagent-driven, started 2026-09-02.

Preflight: mostly clean. One boundary adjustment by controller — plan's global constraint says "change both platforms' aligned prompt in the same task" but Tasks 4 & 5 split the reading-passage CASING prompt (web=T4, Flutter=T5). Resolution: T4 does ONLY the web normalizeTypography wire-in (no prompt); T5 does the casing prompt for BOTH platforms (readingPassage.ts + reading_passage_source.dart) aligned. Noted in T4/T5 dispatches.
Known intentional dup for final review: capitalizeHeadword implemented 3x (web vocabDisplay.ts, Flutter headword_casing.dart, scripts/capitalize-vocab-headwords.js — script can't import cross-package); all checked against the same test table.
Task 1 (normalizeTypography helper): review FAILED — curly-quote char classes contained ASCII quotes not the Unicode chars (both platforms); Flutter space regex was the forbidden literal-space class; tests passed vacuously (ASCII inputs). Root cause: literal Unicode mangled through prompt/context. complete (858097e..c9fde1a incl. Unicode-escape fix, re-review clean). web 736 / Flutter 703, typecheck + analyze clean.
Task 2 (web typing advance-on-length): complete (c9fde1a..ce838f1, review clean — rewritten typo-test verified equivalent). web suite 738, typecheck+build clean.
Task 3 (Flutter typing + normalize + wordMap case bug): implemented (ce838f1..72c76d9), review found 1 Important — generate() feeds lowercased headwords to _buildPrompt (wordMap.keys) diverging from web. Fix 6c1ce08 re-review clean. Task 3 COMPLETE (ce838f1..6c1ce08). reading dir 150, full suite ~709, analyze 12.
Task 4 (web passage normalize wire-in): complete (6c1ce08..19b2e69, review clean). web suite 739.
Task 5 (reading casing prompt, web+Flutter): complete (19b2e69..5af2179, review clean). web 740 / Flutter 710. Minor: 2 of 4 Flutter test assertions non-discriminating (load-bearing 2 work).
Task 6 (capitalizeHeadword helper): complete (5af2179..88b41a2, review clean). web 747 / Flutter 717.
Task 7 (capitalize headword on new-vocab save): complete (88b41a2..4697701, review clean — both deviations verified sound, no assertions weakened). web 748 / Flutter 718, analyze 12.
Task 8 (capitalize-vocab-headwords.js): complete (4697701..4fe0f6a, review clean — emulator suite 4/4 twice). Minor cosmetics noted (batch 400 vs 500, log-before-commit).
Task 9 (listening speaker-reference prompt, web+Flutter): complete (4fe0f6a..ee596f4, review clean). web 749 / Flutter 719. ALL 9 IMPL TASKS DONE.
Task 10 (verification gate): PASS. Web 749 tests + typecheck clean + next build exit 0. Flutter 719 tests + analyze 12 (zero new). Scripts 4/4 with firebase emulators:exec (re-verified by controller). README needs no change (doesn't describe the old exact-match rule). No commit (gate only).

ALL 10 TASKS COMPLETE. Range 858097e..ee596f4 on master (12 commits: T1 + T1-fix + T2 + T3 + T3-fix + T4 + T5 + T6 + T7 + T8 + T9). Final whole-branch review next.
Minor findings carried for final review: T5 2 non-discriminating Flutter test assertions (load-bearing 2 work); T8 batch size 400 vs sibling 500 + log-before-commit ordering (cosmetic); T9 unchanged gender clause still says "speaker A/B" (refers to JSON label, plan-mandated byte-identical); 3 identical capitalizeHeadword copies (web/Flutter/script — intentional, script can't cross-import, all checked against same table).

## Final whole-branch review (opus) — Ready: WITH FIXES
Strengths verified: 2 listening prompts byte-identical after placeholder-normalize (JSON-shape line intact); normalizeTypography \u-escape fix (c9fde1a) is live, web/Flutter identical code-point sets; A1 gate safe vs scoring path; input caps make >= safe; rewritten typing/deletion tests hand-re-derived as faithful; copyWith purely additive; migration updatedAt ISO matches both serializers; 3 capitalizeHeadword copies behaviorally identical.
- IMPORTANT I1: dictation source (apps/web dictation/page.tsx:133 + dictation.ts:43; dictation_source.dart:30,75) has the SAME case-sensitive vocab-word→id map that A3 fixed in reading — B makes it systematically return empty → dictation result shows no practised words + recordDailyActivity under-counts. Silent, untested. Flutter dictation also feeds wordMap.keys to prompt (needs both halves of 6c1ce08). PLAN DEFECT (A3 scoped to reading only).
- IMPORTANT I2: web getVocabRecordByHeadword (vocabRecords.ts:74) exact-match query called with raw lowercase user query at lookup/page.tsx:77 → after B, systematically misses stored "Meticulous" → paid BYOK AI call per repeat lookup. Flutter immune. FIX: capitalizeHeadword(headword.trim()) in getVocabRecordByHeadword.
- IMPORTANT I4: C prompt hard-codes Vietnamese speaker nouns ("người đàn ông"/"khách hàng"/"người nói") into questions the same prompt demands be written in ${languageLabel} (English/zh/ko/ja) → mixed-language question text on push. PLAN DEFECT (plan specified VN strings verbatim). FIX: semantic phrasing ("the man"/"the woman" + "use the natural equivalent in ${languageLabel}"; "the customer, the clerk..."; "the speaker"), both files byte-aligned.
- IMPORTANT I3: web auto-deploys on push, migration is manual after → window where new web saves create duplicate docs (web dup check misses legacy lowercase). NOT code — deploy ordering must be written down: push → verify deployed → dry-run (read camelCase output) → --apply, immediately.
- M1: readingScoring.ts:25,61 comments now factually wrong (A1 deleted the "typed always == target" invariant). Fix in same wave.
- Deferred minors: M2 (fetchSavedExercise doesn't normalize restored passages — A1 gate rescues user), M3 (normalizeTypography gaps ‐‑/more spaces), M5 (script test table missing 2 rows), M6 (2 dead Flutter reading-prompt assertions), M7-M11.
Fix dispatch: 1 agent — I1 + I2 + I4 + M1.
Final-review fix wave: d0332dc (I1 dictation map, both platforms) + f4b8517 (I2 getVocabRecordByHeadword casing + M1 readingScoring comments) + dcffc15 (I4 semantic speaker refs, both listening prompts byte-aligned). web 752 / Flutter 721 / analyze 12. All RED-verified. Re-review clean (Ready: YES). All 4 findings resolved, no remaining issues.

# BUGFIX PLAN 2026-09-02 — COMPLETE (pending user push). Range 858097e..dcffc15 on master (14 commits + spec 0e2b794 + plan 858097e). web 752 / Flutter 721 / analyze 12. origin at efb42c3 (Plan 4).
REQUIRED MANUAL STEP after push (I3): push → confirm apps/web App Hosting deployed → `node scripts/capitalize-vocab-headwords.js` (dry-run, read the from→to list for camelCase like iPhone) → `node scripts/capitalize-vocab-headwords.js --apply`, IMMEDIATELY (window between deploy and migration = web creates duplicate vocab docs).
Deferred minors (not blocking): M2 fetchSavedExercise doesn't normalizeTypography restored web passages (A1 gate rescues user); M3 normalizeTypography missing ‐‑ hyphens + more space widths; M5 script test table missing iPhone/đẹp rows; M6 2 dead Flutter reading-prompt assertions; M7 web capitalize in draft-builder not write-boundary; M8 import-vocab/import.js writes raw headword (re-run would need migration re-run); M9 empty-target sentence dead-end (pre-existing); M11 "Use natural 中文 capitalization" no-op.

---

# FLUTTER BLOOM PLAN 5 (Listening + Word Radar + Progress) — IN PROGRESS
Plan: docs/superpowers/plans/2026-09-03-flutter-bloom-plan5-listening-radar-progress.md (commit b3403e9)
Baseline: master at 9356ed9 (plan doc b3403e9). Flutter 721 tests, analyze 12. 14 tasks.
Execution: subagent-driven. Working on master (user consent, same as Plans 1-4).
Task 1 (BloomStatCard): complete (b3403e9..1971e8d, review clean). +3 tests.
Task 2 (BloomBarChart): complete (1971e8d..5bf4359, review Approved). +4 tests.
  Minor findings for whole-branch review: (1) value caption left-aligned not centered over bar (web .dash-chart-value is centered) — wrap in Center/Align.bottomCenter; (2) magic 14/6 px (brief-dictated CSS-port geometry, off BloomSpacing scale); (3) 10.5px caption in tight SizedBox(14) may clip ~1px — add height:1.0/StrutStyle; (4) analyze checked new files only not full baseline.
Task 3 (BloomAudioControls): complete (5bf4359..15e96b9, review Approved). +5 tests.
  Minor findings for whole-branch review: (1) bloom_audio_controls.dart:132 raw SizedBox(width: 8) should be BloomSpacing.sm; (2) doc-comment has emoji ⏮⏭↺ (repo says avoid emojis in files) — brief-sanctioned, strip if desired.
Task 4 (BloomWordSeekBar): complete (15e96b9..dd72d8c, review Approved, no issues). +3 tests. Bloom suite 79 green. ALL 4 WIDGET TASKS DONE.
Task 5 (Luyện nghe hub): complete (dd72d8c..dcc817d, review Approved). Tests 3/3, analyze 12 (unchanged). Card copy preserved from existing screen.
  Minor for whole-branch review: kept existing icons (edit_note_outlined/quiz_outlined) vs brief's suggested mic_none_outlined/headphones_outlined — brief icons more apt, reconcile in final review.
Task 6 (Nghe chép home): complete (dcc817d..cf45b48, review Approved). Tests 9/9 (plan said 10 — actual file has 9, all green). analyze 12. Frozen surface untouched, strings preserved.
Task 7 (Nghe chép session): complete (cf45b48..0a4477d, review Approved). Tests 18/18, analyze 12 (unchanged). PopScope+BloomScaffold+BloomAppBar; play FilledButton.icon -> BloomAudioControls.playOnly(isPlaying: session.isSpeaking); controls in BloomCard; _SeekSlider raw Slider -> BloomWordSeekBar (kept _restWordIndex/_isDragging state machine, no enable cond in file so enabled default true); free + per-blank TextFields Bloom-styled (surface2 fill, md/sm OutlineInputBorder, accent focus/cursor, mono fontFamilyFallback + tabularFigures); submit -> BloomPillButton. _SpeedSelector left raw. Test: FilledButton->BloomPillButton x16, +BloomAudioControls assertion. Kept local canSubmit var (no session.canSubmit getter exists — brief said session.canSubmit).
  Minor for whole-branch review: InputDecoration sets both border + identical enabledBorder (redundant, harmless — could drop border); _SeekSlider drag-preview Text('Từ n/n') still uncoloured (pre-existing, out of Task 7 scope).
Task 8 (Nghe chép result): complete (0a4477d..89780be, review Approved). Tests 12/12 (file has 12), analyze 12. 4 BloomStatCards (values byte-identical to old _StatCard incl "N (−P%)" seek string w/ U+2212); 2 test finders 'Số lần tua'→'SỐ LẦN TUA' (tracks BloomStatCard.toUpperCase, value asserts unchanged — sanctioned like Plan 2 uppercase headers); body SingleChildScrollView+Column not ListView (matches reading_result Plan4 pattern, lazy ListView hid bottom buttons in test viewport).
  Minor for whole-branch: Column children under-indented ~4sp (dart format would fix; analyze clean).
Task 9 (Nghe hiểu home): complete (89780be..f1f62ac, review Approved). Tests 4/4, analyze 12. _context=AppContext.general untouched, strings preserved, twin of dictation_home.
Task 10 (Nghe hiểu session): complete (f1f62ac..c5a8d22, 2 commits: restyle 01007c4 + fix c5a8d22, re-review Approved). Tests 11/11, full listening 163/163, ANALYZE 10 (was 12 — RadioListTile infos at :185,191 gone). BloomAudioControls.transport, BloomMcOption x12, BloomWordSeekBar. Fix: 1st attempt dropped '— Người nói {speaker}' turn-indicator suffix — restored as standalone Text above seek bar, _SeekSlider ctor reverted, seek label plain 'Tua theo từ'.
  Minor for whole-branch: _previewLabel drag-preview Text still bare/unstyled (pre-existing, inside frozen _SeekSlider state).
Task 11 (Nghe hiểu result): complete (c5a8d22..a4b4c4c, review Approved, no issues). Tests 8/8 (7 orig + 1 additive BloomMcOption test), full listening 164/164, analyze 10. check_circle/cancel icons kept+recoloured, BloomMcOption read-only breakdown, transcript speaker scheme preserved. ALL LISTENING SCREENS DONE.
Task 12 (Progress dashboard): complete (a4b4c4c..7820ffe, review Approved). NEW test file progress_screen_test.dart 5/5, full practice 54/54, analyze 10. Deleted _WeeklyChartPainter CustomPainter + 4 private widgets; BloomStatCard x2, BloomBarChart, BloomProgressBar CEFR rows. Real strings preserved (7 ngày qua / Theo cấp độ / Chưa có streak / Ôn N từ ngay). CEFR basis count/totalCount matched. _startDueSession context.push frozen.
  Minor for whole-branch: (1) 'ngày liên tiếp' styled w800/ink not brief's 13/inkSoft (preserves old titleMedium hierarchy); (2) kept 3rd streak Text 'Tiếp tục giữ streak nhé!'/'Bắt đầu hôm nay nhé!' (preserves copy brief tree would drop); (3) chart-before-CEFR order (not frozen); (4) test2 /practice/session stub doesn't capture extra; (5) _dateKey duplicated test<->prod.
Task 13 (Word Radar screen): complete (7820ffe..c82dddb, review Approved). Tests 15/15 (10 word_radar + 5 bloom_text_field incl new inputFormatters-truncation test), analyze 10. Added BloomTextField.inputFormatters passthrough (additive). LengthLimitingTextInputFormatter(3000) replaces maxLength:3000 (grapheme-count equivalent). Scan wiring + _HighlightedText partitioning + _openKnownWord frozen. Amber AI-hint, sage highlight spans.
  Minor for whole-branch: hint kept 'Dán văn bản vào đây...' vs brief's 'Dán đoạn văn cần quét...' (less churn); redundant SizedBox(infinity) around block BloomPillButton; single-child spaceBetween Row on char counter.
Task 14 (Word Radar suggestion sections): complete (c82dddb..7c3d36c, review Approved). word_radar tests 45, FULL SUITE 743 (>721), analyze 10. Both widgets -> BloomCard/BloomPillButton/BloomCefrPill, check_circle/close icons kept, aiEnabled gate unchanged.
  Minor for whole-branch: ipa separator 'ipa  •  meaning' -> conditional 'ipa • meaning' / bare meaning (cosmetic improvement, flagged); card spacing via Padding(bottom:8) not Card margin.

# ALL 14 TASKS COMPLETE. Range b3403e9..7c3d36c on master. Flutter 743 tests (was 721), analyze 10 (was 12). Final whole-branch review next.

## Final whole-branch review (opus) — Ready: WITH FIXES
Strengths: token discipline perfect (1 sanctioned Colors.transparent); analyze confirmed 10, no new lint; frozen behavior byte-identical across all 7 screens; PopScope complete; visual consistency w/ Plan 4 excellent (_ListeningCard == _ReadingCard); BloomTextField.inputFormatters backward-compat safe; VocabSuggestionsSection holds at all 6 call sites.
- IMPORTANT I1: dictation_session_screen.dart:150-156 — BloomAudioControls.playOnly(isPlaying: session.isSpeaking) shows "Dừng"+stop icon for the WHOLE playback (synthesize awaits completion, not "briefly" as plan L470 wrongly assumed), but there's no stop path — tapping re-enters play() → replayCount+1 (a SCORED penalty). PLAN DEFECT, faithfully implemented. FIX: pass isPlaying: false at the dictation call site (restores pre-Bloom always-"Nghe lại"+play behavior).
- IMPORTANT I2: bloom_audio_controls.dart:40-42 — .transport Row (no Flexible/FittedBox) ≈288px content vs ≈296px avail at 360dp → overflows at ≤320dp or text-scale ≥1.25. Regression (old 4 bare IconButtons ~200px). FIX: FittedBox(fit: BoxFit.scaleDown) + mainAxisSize.min, or gaps → BloomSpacing.sm.
- Nits folded into same fix: bloom_audio_controls.dart:8 emoji ⏮⏭↺ in doc comment; :98 raw SizedBox(width: 8) → BloomSpacing.sm.
- Deferred to Plan 6 (reviewer triaged): BloomBarChart caption alignment + magic px; hub icons OK as-is; border+enabledBorder harmless; _SeekSlider drag-preview Texts (frozen); Task-12 streak typography/3rd-Text (preserving copy = right call); Task-13 hint string (don't change copy in restyle); Task-14 ipa separator (improvement); word_radar textTheme section headers → BloomSectionHeader; extract shared BloomNavCard; Progress chart-mapping test gap (add in Plan 6); listening results scroll-buttons-off-bottom divergence (deliberate).
Fix dispatch: 1 agent — I1 + I2 + 2 nits, all in 2 files.
Final-review fix wave: baef691 (I1 dictation isPlaying:false + I2 FittedBox transport + 2 nits). bloom_audio_controls 5/5, dictation_session 18/18, comprehension_session 11/11, analyze 10. Re-review: Ready YES, no regressions.

# FLUTTER BLOOM PLAN 5 — COMPLETE. Range b3403e9..baef691 on master (16 commits). Flutter 743 tests (was 721), analyze 10 (was 12). All 14 tasks + final-review fix wave done, all reviews clean. NOT pushed (origin at bfb7052... actually check).

---

# FLUTTER BLOOM PLAN 6 (Settings + Sign-in + C2 + theme picker + cleanup) — IN PROGRESS
Plan: docs/superpowers/plans/2026-09-03-flutter-bloom-plan6-settings-signin-cleanup.md (commit ece08c5)
Baseline: master at af5cef9 (plan doc ece08c5). Flutter 743 tests, analyze 10. 13 tasks. Target: analyze 0.
Execution: subagent-driven. Working on master (user consent, same as Plans 1-5).
Task 1 (BloomSwitch): complete (3fd6f06..e8a51b7 — impl edb751b + clip fix e8a51b7, review Approved). +4 tests, analyze 0. Switch colors activeTrackColor/activeThumbColor/inactiveTrackColor/inactiveThumbColor.
Task 2 (BloomSegmented<T>): complete (e8a51b7..48d8ebb, review Approved). +4 tests (incl ThemeMode value type), analyze 0. Generic pill segmented control, clipBehavior present.
Task 3 (BloomNavCard): complete (48d8ebb..a787e9b, review Approved, no issues). +3 tests, analyze 10 (0 new). Extracted _HubCard body verbatim, 11 call sites migrated (reading 4 + listening 2 + practice 5), 3 private widgets deleted, -159 lines.
Task 4 (C2 practice area): complete (a787e9b..3f5d91a, review Approved, no issues). Tests 53 practice / 753 full (743 + Tasks1-3's 11 new - 1 deleted toggle test), analyze 10. generate_exercise_use_case drops aiEnabled param; practice_session_provider aiEnabled->aiAvailable. practice_session_provider_test.dart does not exist.
Task 5 (C2 dictionary area): complete (3f5d91a..69535f9, review Approved). Tests 84 dict / 753 full, analyze 10. Pure aiEnabled->aiAvailable rename in 5 lookup-chain files; mockito regen (lookup_use_case + lookup_provider mocks); search_bar_widget_test harness -> providerConfigs ciphertext. Also fixed lookup_provider_test (brief gap). 3 .g.dart hash-only refreshes swept in (inert).
Task 6 (C2 word_radar area): complete (69535f9..db585f3, review Approved). Tests 45 word_radar, analyze 10. 3 gate renames (word_radar_provider scan+retry, result_suggestions_section _load); 3 test harnesses -> providerConfigs ciphertext. grep aiEnabled word_radar = 0 (lib+test). word_radar_screen_test frozen 'Bật AI trong Cài đặt' assertion kept.
  Minor: 3 test description strings still say 'AI disabled/enabled' (accurate, deferred).
Task 7 (HomeNoticeCard + AiKeyMissingCard + 6 home gates): complete. git mv ai_disabled_card->home_notice_card (class rename, behaviour unchanged); new AiKeyMissingCard (fixed copy + 'Mở Cài đặt'->/settings). 6 home screens: !aiEnabled->!aiAvailable + AiKeyMissingCard; reading/comprehension/dictation non-AI branches AiDisabledCard->HomeNoticeCard (same strings). 6 test harnesses -> C2 providerConfigs pattern + /settings stub route; AI-off tests renamed 'shows the missing-API-key card when no key is set'. grep aiEnabled/AiDisabledCard in reading+listening+core/widgets = 0. Scoped tests +29 pass; analyze 10 (0 new).
  KNOWN PRE-EXISTING (not Task 7): 6 *_result_screen_test.dart failures ('loads new-word suggestions' verify) — Task 6's result_suggestions_section aiAvailable flip left those result-screen harnesses on aiEnabled:true/no-key. Needs a Task 6 follow-up.
Task 7 (AiKeyMissingCard + HomeNoticeCard rename + 6 home gates): complete (db585f3..a99730e — impl 3023641 + Fix 1 a99730e, review Approved). Full suite 755/0, analyze 10. HomeNoticeCard = pure rename of AiDisabledCard; new AiKeyMissingCard (fixed copy + Mở Cài đặt -> /settings); 6 home screens AI-off branch -> !aiAvailable + AiKeyMissingCard, other branches -> HomeNoticeCard. 6 home-screen + 5 result-screen test harnesses -> providerConfigs ciphertext.
  LESSON: Task 6 review only ran test/features/word_radar/ and missed 6 result-screen tests that embed result_suggestions_section — when a SHARED widget's gate changes, the review must run every consuming screen's tests. Fixed in Task 7 Fix 1.
  C2 runtime reader migration COMPLETE. grep aiEnabled lib/ now = only user_settings_state.dart (Task 8) + user_settings_provider.dart (Task 8) + settings_screen.dart:51,54 (Task 9 toggle).
Task 8 (C2 finalize — delete aiEnabled field): complete (a99730e..f12c590, review Approved). Full suite 755/0, analyze 10. Field + ctor + copyWith + defaults + setAiEnabled + 'ai_enabled' prefs all deleted; aiAvailable getter kept (doc trimmed). Minimal settings de-toggle (Provider/Model/API-Key now unconditional). grep aiEnabled lib/+test/ = ZERO. C2 COMPLETE.
  Minor (process): implementers running whole-file dart format on non-format-clean files inflates review diffs — prefer scoped format or a one-time repo format-clean.
BASELINE now: 755 tests, analyze 10. Tasks 1-8 done.
Task 9 (Settings screen Bloom + Giao diện picker): complete (f12c590..d9c9f70, review Approved). ANALYZE 2 (was 10 — 8 settings RadioListTile infos gone via showSingleSelectSheet). NEW settings_screen_test.dart 6 tests. Full suite 761 (+6). BloomScaffold/BloomCard-per-section/BloomSectionHeader; Provider+theme -> BloomSegmented; reminder -> BloomSwitch; ListTiles -> FilterTile; _SignedInSection gradient avatar + danger sign-out pill; CEFR/model pickers -> showSingleSelectSheet + link BloomPillButton for custom model. _ModelTile ConsumerWidget->StatelessWidget (never read ref).
  Minor for whole-branch: API-key save spinner replaces the 'Lưu' pill (BloomPillButton no child slot); no test for CEFR-null picker path; signed-out 'Tài khoản' card is header-over-empty.
Task 10 (Sign-in screen Bloom): complete (d9c9f70..66f968f, review Approved). NEW sign_in_screen_test.dart 3 tests, full suite 764 (+3), analyze 2. build() only — BloomScaffold + BloomLeafMark(40) + LexiCore + BloomPillButton (Google primary / Thử lại secondary) + context.bloom.danger errors. _signIn() byte-identical.
  Minor for whole-branch: _Step.migrating subtitle + _migrationError block untested (un-fakeable: HiveMigrationService new'd, FirebaseAuth.instance throws in tests — needs a DI seam that would violate frozen _signIn). Test 3 asserts Google button reappears not a 'Thử lại' button (frozen screen only shows Thử lại for _migrationError — correct reading).
Task 11 (speed selectors -> BloomSegmented): complete (66f968f..be1588f, review Approved, no issues). Tests 29 target / 164 listening, analyze 2. Labels '0.75x'/'1x'/'1.25x' preserved verbatim. grep SegmentedButton lib/ = 0 (all raw SegmentedButton retired).
Task 12 (RadioGroup migration + minors): complete (be1588f..a6fa0bc, review Approved). ANALYZE 0 (was 2 — "No issues found!"). Full suite 764/764. selection_sheets single-select: RadioListTile -> tappable ListTile + radio Icon (fallback; RadioGroup rejected — it suppresses onChanged on re-tap of current value, breaks CEFR-null + re-confirm). Return contract Future<SelectOption<T>?> byte-identical. bloom_bar_chart caption centered + height:1.0 + named consts. word_radar 'Văn bản'/'Bản dịch' -> BloomSectionHeader (VĂN BẢN/BẢN DỊCH).
  Minor for whole-branch: (1) subtle behavior change — re-tapping the already-selected picker row now confirms-and-closes (old did nothing); benign (callers apply picked.value, no-op for current). (2) single-select rows lost radio a11y semantics (per brief fallback). (3) BloomSectionHeader 18px top padding loose inside word_radar BloomCards.
Task 13 (docs): complete (a6fa0bc..811d598, review Approved). README + CLAUDE.md only. Test count 474->764, aiEnabled dropped from Cấu hình AI/sync list/schema, theme picker + retired-Material-widgets documented. analyze 0.
  Minor for whole-branch: README:88 'Gợi ý từ mới (cần bật AI)' still says 'bật AI' not 'cần API key'; README Firestore-sync prose/schema was ALREADY stale vs AiSettingsSyncService (settings/config not settings/user) - pre-existing, needs own docs pass.

# ALL 13 TASKS COMPLETE. Range ece08c5..811d598 on master. Flutter 764 tests (was 743 pre-plan), ANALYZE 0 (was 12 at Plan 5 end / 10 at Plan 6 start). C2 fully done. Final whole-branch review next.

## Final whole-branch review (sonnet; opus attempt rate-limited) — Ready: YES
No Critical/Important. Verified: analyze 0; C2 provably complete (grep aiEnabled lib/+test/ = 0, full suite green = compile proof); AiKeyMissingCard nav safe (all 6 gates + /settings in same ShellRoute); theme picker wired end-to-end to real setThemePreference; ~25 harness conversions uniform (all activeProvider=gemini default); BloomSegmented can't RenderFlex-overflow (Expanded segments soft-wrap); settings/sign-in frozen surfaces preserved.
Minor findings: (1-3) README fixes (activeContext in settings schema, Bảo mật sync-fields inaccurate, line 88 'cần bật AI') — FIXED in 0308e40; (4) single-select sheet rows lost radio a11y semantics — deferred (Semantics wrap would restore cheaply); (5) re-tap-selected-row now confirms-and-closes (benign, idempotent setters); (6) 3 stale test description strings; (7) BloomSegmented<AiProvider> label-width tight at ~1.3x text scale (soft-wraps, no crash). Coverage gaps acknowledged: sign-in migration flow (un-fakeable, needs DI seam — backlog), CEFR-null picker path (correct by inspection, untested).
STATE OF MIGRATION: Flutter app effectively FULLY on Bloom. All 6 feature areas + shared widgets via lib/core/theme/bloom/. Raw SegmentedButton/Switch/RadioListTile retired app-wide (analyze 0). "Bật AI" toggle gone. Remaining Material (AlertDialog/showTimePicker/LinearProgressIndicator) is deliberate — AppTheme Bloom-maps ThemeData for those.

# FLUTTER BLOOM PLAN 6 — COMPLETE. Range ece08c5..0308e40 on master. 764 tests (was 743), analyze 0 (was 12). 13 tasks + 2 in-task fixes + 1 final-review README fix, all reviews clean. Ready to merge. THE 6-PLAN BLOOM REDESIGN IS DONE.

---
# POST-DEVICE-TEST PUNCH LIST (user's ~17 items → 8 sub-projects SP-1..SP-8)
SP-1 crash+translation-btn+bottomnav: DONE c27cdcd. SP-2 contrast+flashcard: DONE a33d16f. SP-3 submit-count+speed-slider+listen-btns: DONE 608a785. SP-4 streak Firestore sync: DONE cec92ca.
User instruction 2026-09-03: "Chạy tuần tự đến SP cuối cùng không cần hỏi lại" — run SP-5..8 autonomously via spec→plan→SDD.
SP-5 = port web savedReadingExercises + savedListeningExercises to Flutter (Lưu bài / Lấy bài có sẵn) — bilingual + part5/6/7 + dictation + comprehension. SP-6 = 4 IA changes (Tiến độ tab, inline reading/listening sub-hub options, web Radar→sidebar, bank search/filter parity). SP-7 = MC/fill/translation exercises in web practice. SP-8 = app icon (leaf mark).

## SP-5 execution (plan 9709123, 9 tasks)
Task 1 (entity JSON round-trips): complete (9709123..17e9a38, review Approved). +13 tests (793 total), analyze 0. Part5/6/7 sets+children, DictationItem, BlankSpan, ListeningPassage/Turn/Question got toJson/fromJson; ReadingPassage already had it. speakerGenders round-trips + assignVoices verified distinct.
  CARRY TO TASK 2/3: (a) ReadingPassage.fromJson + BilingualSentence.fromJson use UNGUARDED hard casts (pre-existing) — the service must merge the wrapper doc's fields (id/level/context/targetLanguage/generatedAt) into the passage map BEFORE calling ReadingPassage.fromJson, or it crashes on a web-saved minimal doc. Same for Part5/6/7 sets (their fromJson tolerates missing extras — OK) and ListeningPassage (tolerates).
  (b) BilingualSentence per-sentence key: Flutter `vocabIds` vs web `vocabWords` — only real per-field mismatch, degrades to [] not crash, acceptable for reuse.
  Minor for whole-branch: EconomyVolume.values.byName unguarded (part5/6/7_*.dart) inconsistent w/ defensive style; BlankSpan.fromJson hard casts (not in persisted shape); no explicit "load web-minimal doc" test for Set/Passage entities; not test-first.
Task 2 (SavedExercisesService + filter model): impl b2752a8 + controller fix ad6c66a. +26 service tests (819 total), analyze 0. saved_exercise.dart (SavedExerciseType enum, .collection, .bodyKey), saved_exercises_service.dart (save/getRandom/usedBilingualVocabIds), savedExercisesServiceProvider. Matching predicates ported from web verbatim EXCEPT matchesComprehension (plan §16/§84 deliberately specify a CEFR ceiling; web source does exact level equality — plan-mandated divergence, kept, note for whole-branch).
  CONTROLLER FIX ad6c66a: subagent wrote body key `passage` for all 6 types; web savedListeningExercises.ts uses `item`. Added SavedExerciseType.bodyKey (item for listening, passage for reading) + 2 web-minimal-doc load tests. Reading side was already compatible.
  CARRY TO TASK 3+: getRandom returns the raw body map under key `passageJson` regardless of collection. Task 5/6 callers pass result.passageJson to <Entity>.fromJson. For bilingual, per CARRY(a) from Task 1 the caller must merge wrapper fields before ReadingPassage.fromJson — but getRandom does NOT return the wrapper; Task 5 brief must handle: the web-saved bilingual `passage` sub-object already carries its own id/level/context/targetLanguage/generatedAt (web writes the full ReadingPassage JSON as `passage`), so ReadingPassage.fromJson works directly. Verify against a real web doc during Task 5.
  Task 2 review: Approved (spec compliant, quality Approved, Minors only). Post-review fix 011ba87: createdAt->UTC, +part6/7/comprehension round-trips. complete (17e9a38..011ba87). 821 tests, analyze 0.
Task 3 (reading loadSaved + carry filters): complete (011ba87..9a99902, review Approved, no findings). +4 tests (163 reading / ~825 total), analyze 0. ReadingSessionState & ReadingSessionResult each +`String? reusedFromId` +`Map<String,dynamic>? generationFilters` (nullable, copyWith passthrough). generate() +optional generationFilters param. loadSaved(ReadingPassage, {String? savedId, Map<String,dynamic>? generationFilters}). session_screen threads both state->result. Pattern for Task 4's 5 notifiers.
Task 4 (loadSaved on part5/6/7 + dictation + comprehension): impl a8d64e5. +15 tests (840 total), analyze 0. Same pattern as Task 3: each *SessionState & *SessionResult +String? reusedFromId +Map? generationFilters (nullable, copyWith passthrough); generate() +optional generationFilters; loadSaved(<Set/Item/Passage>, {String? savedId, Map? generationFilters[, DictationDifficulty difficulty]}). 5 session screens thread state->result.
  CONCERN: subagent did NOT run `dart format` — SDK 3.11.5 tall-style reflows untouched code + breaks a listening_comprehension_provider.dart `if(x) return; //c` into curly-braces lint. Hand-formatted additively instead. Task 3's committed file also fails current dart format. => repo-wide format-tool drift; decide at whole-branch whether to do a one-shot repo format+fix.
  Task 4 review: Approved (spec ✅, quality Approved, no Critical/Important). complete (9a99902..a8d64e5). 840 tests, analyze 0 (reviewer re-ran scoped analyze). dart-format drift = whole-branch Minor.
Task 5 (reuse on bilingual home + prioritizeUnusedWords): impl fe25006. +3 screen tests (7 reading_home / 175 reading / ~843 total), analyze 0. prioritizeUnusedWords = top-level fn in saved_exercises_service.dart (List<VocabRecord>, Set<String>) -> unused-first stable partition. _reuse filter map: {'topicIds': _topicIds.toList(), 'maxCefr': _level?.name, 'wordCount': _wordCount} — SAME map to getRandom + loadSaved(generationFilters:). Button: data: builder wrapped in Column(min,stretch)[primary 'Tạo bài luyện', SizedBox(10), secondary 'Lấy bài có sẵn']. _generate applies prioritizeUnusedWords(prioritized, usedIds) before .take.
  Task 6 mirrors _reuse for part5/6/7 (ToeicFilters {topicIds, volumes}) + dictation ({difficulty}) + comprehension ({context, level}).
  Task 5 review: Approved (spec ✅, quality Approved, Minors only). complete (a8d64e5..fe25006). 175 reading tests, analyze 0.
Task 6 (reuse button on part5/6/7 + dictation + comprehension homes): DISPATCHED. Filter maps: TOEIC {'topicIds': [], 'volumes': _volumes.map((v)=>v.name)}; dictation {'difficulty': _difficulty.name}; comprehension {'context': _context.name, 'level': _level?.name (nullable=any, matches web savedLevelFilter)}. AppContext.name / DictationDifficulty.name / EconomyVolume.name / CEFRLevel.name all match web wire values (verified).
Task 6: impl 13e09b0. +15 tests (858 total), analyze 0, dart format clean. 4 homes get 'Lấy bài có sẵn' secondary button (Column wrap of data: builder). _reuse per brief. Entity fromJson lives in part5_question.dart/part6_passage.dart/part7_passage.dart (not *_set.dart).
  Task 6 review: Approved (spec ✅, quality Approved, Minors only). complete (fe25006..13e09b0). 858 tests, analyze 0.
Task 7 (Lưu bài on bilingual result + thread generationFilters into generate()): DISPATCHED. _save uses result.generationFilters ?? minimal {topicIds:[], maxCefr: passage.level.name, wordCount: null}. reading_home _generate now passes generationFilters: filters (same map as _reuse). _savedId seeded from result.reusedFromId -> "Đã lưu bài này" text instead of button.
Task 7: impl 5b650b3. +4 tests (188 reading / ~862 total), analyze 0. reading_result_screen: _saving/_savedId (seeded from result.reusedFromId), parameterless _save() (brief's _save(context,ref) tripped use_build_context_synchronously), "Lưu bài"/"Đang lưu…" secondary btn <-> "Đã lưu bài này" text. reading_home _generate threads generationFilters. Report RECOMMENDS Task 8 extract shared SaveExerciseButton ConsumerStatefulWidget + retrofit reading_result_screen.
  Task 7 review: Approved (spec ✅, quality Approved, no Critical/Important). complete (13e09b0..5b650b3). 188 reading tests, analyze 0.
Task 8 (shared SaveExerciseButton + Lưu bài on all 5 AI result screens): DISPATCHED. New lib/core/widgets/save_exercise_button.dart (ConsumerStatefulWidget: type, reusedFromId, buildPassageJson closure, generationFilters resolved-by-caller, targetLanguage). Retrofit reading_result_screen. Per-type fallback filters: TOEIC {topicIds:[],volumes:[]}; dictation {difficulty: result.difficulty.name}; comprehension {context: passage.context.name, level: passage.level.name}. All 5 entities carry targetLanguage.
Task 8: impl 3d608a9. suite 862->870. analyze 0. SaveExerciseButton in lib/core/widgets/. All 5 AI result screens have "Lưu bài" (or "Đã lưu bài này" when reused). reading_result_screen retrofitted (3 save tests -> widget test).
  Task 8 review: Approved (spec ✅, quality Approved, no Critical/Important). complete (5b650b3..3d608a9). 870 tests, analyze 0.
Task 9 (full-suite gate + README): DONE (no subagent - controller). flutter analyze 0, flutter test 870/870. README: "Lưu / dùng lại bài AI" para under reading hub + Firestore struct (reading_exercises/listening_exercises) + Roadmap checkmark. Security rules unchanged (users/{uid}/{document=**} wildcard already covers it).
# SP-5 ALL 9 TASKS COMPLETE. Range a8d64e5-parent(9a99902..) actually 9709123..<task9> on master. 870 tests (was 780 pre-plan / 793 after Task 1). analyze 0. Whole-branch review next.

## SP-5 whole-branch review (opus) — Ready: NO (2 Critical + 2 Important, all bilingual cross-platform round-trip)
C1: ReadingPassage.fromJson/BilingualSentence.fromJson hard-cast id/level/context/targetLanguage/generatedAt — web saves only {sentences,vocabIds} for bilingual => throws inside un-try'd _reuse => "Lấy bài có sẵn" silently dead. (Task-2 ledger note "web writes full ReadingPassage JSON" was WRONG.)
C2: BilingualSentence.toJson writes vocabIds; web BilingualSentence = {target,vietnamese,vocabWords} => web PassageReview/highlightVocabWords crashes on undefined.length for a Flutter-saved bilingual.
I1: TOEIC _generate never threads generationFilters => every Flutter-saved part5/6/7 doc has volumes:[] (hardcoded result-screen fallback) => Vol filter inert both platforms.
I2: comprehension/bilingual _reuse doesn't restore level/context/targetLanguage from wrapper — guarded defaults (a1/general/english) => wrong CEFR for ResultSuggestionsSection, wrong TTS lang.
Minors: dart format drift is repo-wide 118/325 files pre-existing => separate chore commit, NOT here; web-doc tests never call fromJson; dead `words` param in reading/dictation _reuse; matchesComprehension ceiling = plan-mandated, document only.
FIX WAVE: DISPATCHED (one subagent, all findings).
FIX WAVE df99778: all C1/C2/I1/I2 + minors FIXED, re-review Ready:YES, no regressions. 879 tests (was 780 pre-SP5), analyze 0.
# SP-5 COMPLETE & READY. Range 9709123..df99778 on master (13 commits). Cross-platform bilingual+listening reuse now works both directions. dart-format repo drift (118/325 files) deferred to a standalone chore commit.

---
# SP-6 (IA changes) — spec+plan committed. 8 tasks. spec 2026-09-04-sp6-ia-changes-design.md, plan 2026-09-04-sp6-ia-changes.md.
6a Tiến độ tab (Flutter) / 6b inline reading+listening hub options (Flutter) / 6c web Radar->sidebar / 6d bank filter parity (web search + app dueOnly/CEFR).

## SP-6 execution
Task 1 (Tiến độ tab): impl 617c3fc. suite 881 (+2), analyze 0. /progress top-level ShellRoute child; app_shell 5th _Dest (Icons.insights, idx 3); practice_hub drops Tiến độ card (4 left); progress_screen both appbars lose back button + loading branch gains appbar. BloomBottomNav handles 5 @ 320dp (no fix needed).
  Task 1 review: Approved (spec ✅, quality Approved). complete (dd64a5d..617c3fc). 881 tests, analyze 0.
Task 2 (web Radar -> sidebar): impl 07ff4b1. git mv reading/word-radar -> word-radar (/word-radar route). Sidebar new "Quét từ" group. reading hub card removed. web 753 tests pass, typecheck clean.
  Task 2 review: Approved (spec ✅, quality Approved, no findings). complete (617c3fc..07ff4b1). web 753 tests, typecheck clean.
Task 3 (web bank search box): impl 429d98e. vb-search input (aria-label "Tìm từ") + clear btn above vb-toolbar; folded into filtered useMemo + filterSignature + clearFilters. filterActive extended locally (query counts). web 756 pass (+4), 1 PRE-EXISTING unrelated flake (listening/dictation seek-slider, order-dependent, passes in isolation). typecheck clean.
  review: Approved.
Task 4 (app bank dueOnly+CEFR filter): impl 3927640. NEW lib/core/widgets/vocab_filter.dart (VocabFilterState/vocabRecordIsDue/matchesVocabFilters mirror web vocabFilters.ts). Due chip (Builder, N from vocabAsync.valueOrNull) above topic FilterTile; CEFR FilterTile after it. +17 tests (898 total), analyze 0.
  review: Approved.
Task 3 review: Approved (spec ✅, quality Approved). complete (07ff4b1..429d98e).
Task 4 review: Approved (spec ✅, quality Approved, Minors only — isActive unused yet). complete (429d98e..3927640). 898 tests, analyze 0.
Task 5 (extract reading *Options widgets): impl 642b90d. ReadingBilingualOptions/Part5Options/Part6Options/Part7Options ConsumerStatefulWidget in reading/presentation/widgets/, build returns bare Column. *HomeScreen thin StatelessWidget wrappers (SingleChildScrollView+pad+appbar). Tests unchanged 195, analyze 0. Clean move.
  Task 5 review: Approved (faithful refactor, no drift). complete (3927640..642b90d). 195 reading tests, analyze 0.
Task 6 (inline Reading hub): impl cdc5b0e. ReadingHubScreen StatefulWidget, _expanded string, BloomNavCard onTap toggles (no nav), *Options renders below expanded card. No AnimatedSize. hub test rewritten 6->4 tests (old nav-assertion tests obsolete — cards no longer navigate). reading tests 195->194. analyze 0.
  Task 6 review: Approved (spec ✅, quality Approved; test -1 acceptable — obsolete nav-assertions removed, replaced w/ real expand/collapse tests). complete (642b90d..cdc5b0e). 194 reading tests, analyze 0.
Task 7 (listening Options + inline hub): impl ed1f7c6. DictationOptions/ComprehensionOptions extracted (verbatim), *HomeScreen thin wrappers. ListeningHomeScreen StatefulWidget _expanded, cards toggle. dictation/comprehension home tests unchanged (12/7), listening_home_screen_test 3->4. listening 185->186, analyze 0.
  Task 7 review: Approved (faithful refactor + correct hub). complete (cdc5b0e..ed1f7c6). 186 listening tests, analyze 0.
Task 8 (gate + docs): DONE (controller). Flutter analyze 0 / test 898. Web typecheck clean / test 757 (82 files). README updated: bank filter parity line, reading/listening hub "options inline" note, Word Radar web-sidebar note, Tiến độ tab note, roadmap entry.
# SP-6 ALL 8 TASKS COMPLETE. Range dd64a5d..<task8> on master. Flutter 898 tests (was 879), analyze 0. Web 757 tests, typecheck clean. Whole-branch review next.

## SP-6 whole-branch review (opus) — Ready: YES, no Critical. 3 Important + minors.
I1: reading_bilingual_options.dart:~255 unguarded ref.read after `await usedBilingualVocabIds()` -> StateError if card collapsed mid-fetch (only bilingual; others read-before-await). Fix: hoist notifier read above await or `if(!mounted) return`.
I2: collapse-mid-generate silently drops in-flight AI result (all 6 autoDispose practice notifiers; *Options is sole listener). Re-expand shows fresh AsyncData(null), no loading indicator -> user re-fires. Fix: block hub toggle while that type's sessionAsync.isLoading.
I3: neither inline-hub test taps "Tạo bài luyện"/"Lấy bài có sẵn" — the ONE nav path SP-6 re-routed is uncovered (stub routes declared, never reached).
Minors: .vb-search input missing `font-family: inherit` (renders in browser default font); VocabFilterState.isActive unused + no Flutter "clear filters" affordance (web has vb-chip-clear); redundant intermediate *Options mount per hub-generate (wasted work only, skip); word-radar/page.tsx:109 stale "Bật AI" copy (unrelated, skip).
FIX WAVE: DISPATCHED (I1+I2+I3 + 2 minors).
FIX WAVE 1b65df2: I1 (mounted guard), I2 (hubs -> ConsumerStatefulWidget, block toggle while expanded type isLoading + SnackBar), I3 (reuse-path nav tests both hubs), M1 (.vb-search font-family: inherit), M2 (Xoá lọc chip + wire isActive). 903 tests (+5), analyze 0, web typecheck clean.

---
# SP-7 (web practice AI exercise types) — spec+plan committed. 7 tasks. Web-only. Port Flutter's MC/fill/translation SM-2 exercises to /practice (currently flashcard-only). No standalone drill-picker (out of scope).

## SP-7 execution
Task 1 (practiceExercise.ts): impl 6639ffa. PracticeExercise union + buildExercisePrompt (LANGUAGE_LABELS) + parseExercise (typeof/Array.isArray guards, no throw -> flashcard) + generateExercise (try/catch -> flashcard). 10 tests, typecheck clean.
Task 2 (pickExercise.ts): impl b4e0a3f (controller, trivial). shouldUseFlashcard(record, aiAvailable, rng). 5 tests, typecheck clean.
  Review (1+2): Approved (faithful port, no blocking drift). complete (803dbe2..b4e0a3f).
Tasks 3-5 (MC/Fill/Translation cards): impl 2177b93. All "use client", prop = Extract<PracticeExercise,{type}> + onGrade(1|5). MC 800ms auto, Fill 1200ms auto (Enter submits), Translation manual self-grade. .pe-* CSS. 16 tests, typecheck clean.
  Review (3-5): Approved (matches Flutter UX, contract exact). complete (b4e0a3f..2177b93). 16 tests. Minor: input aria-label (fold into Task 6).
Task 6 (wire practice page): impl d149be4. exercises: (PracticeExercise|null)[] parallel to sessionWords; generateAt reads exercisesRef (no stale closure) + sessionTokenRef guard; lookahead: start seeds 0+1, each non-final grade seeds current+1 & current+2. Render 4-way type switch, .pe-loading spinner while null. aria-labels added to Fill input + Translation textarea. web 791 pass (was ~757), typecheck clean.
  Review: Approved (spec ✅, quality Approved). Re-derived fp boundary math independently, confirmed correct (round-half-to-even lands 0.3+0.7 on exactly 1.0). complete (f620112..855271c).
Task 6 review: Approved (spec ✅, quality Approved; stale-closure + token guards verified correct, SM-2/result effect byte-unchanged). complete (2177b93..d149be4). web 791 tests. Minors: handleGrade seeds +1 AND +2 (dup generateExercise call possible if +1 in-flight — wasted BYOK only), activeConfig not memoized, .pe-loading no aria-live.
Task 7 (gate + docs): DONE (controller). web typecheck clean / test 791. README "Luyện tập cách khoảng" updated (types now on web too, flashcard-mix rule spelled out) + roadmap entry.
# SP-7 ALL 7 TASKS COMPLETE. Range 803dbe2..<task7> on master. web 791 tests (was ~757), typecheck clean. Flutter untouched. Whole-branch review next.

## SP-7 whole-branch review (opus) — Ready: YES, no Critical. 2 Important + minors.
I1: page.tsx handleGrade seeds generateAt(+1) AND (+2); +1 fires a 2nd real generateExercise when the prior +1 call is still in flight (probe confirmed {"2":2}). Wasted BYOK only, no clobber. Spec §4 miss (not task drift). FIX: drop the +1 seed, keep +2 (Flutter's single _generateAt(nextIndex+1)); coverage verified intact.
I2: no committed multi-word mixed-type page test — Fill/Translation never drive real handleGrade. Probe passed. FIX: add it.
Minors: MC page test 200ms from flaking (findByText default 1000ms vs 800ms timer -> {timeout:3000}); parseExercise accepts options:[] / OOB correctIndex -> dead-end unrecoverable session (Flutter parity, cheap to harden web-side); .pe-loading no role="status"; stripPrompt .replace vs Flutter .replaceAll.
FIX WAVE: DISPATCHED (I1+I2 + minors).
FIX WAVE a8d8be7: I1 (drop +1 lookahead seed, keep +2), I2 (multi-word mixed-type page test: MC/fill/translation qualities [1,5,5]), M1 (MC test timeout 3000), M2 (parseExercise MC requires options>=2 + in-range correctIndex else flashcard), M3 (.pe-loading role="status"), M4 (stripPrompt .replaceAll). web 795 tests (+4), typecheck clean.
FIX WAVE re-review: all 6 FIXED, no regressions. web 795 tests, typecheck clean. Ready YES.
# SP-7 COMPLETE & READY. Range 803dbe2..a8d8be7 on master. web 795 tests (was ~757). Flutter untouched.

---
# SP-8 (app icon) — spec 2026-09-04-sp8-app-icon-design.md. DONE (controller — asset generation, no subagent).
Bloom leaf mark (accent #C9587A -> sage #6F9A87 gradient, border-radius 50/50/50/6%, on #FFF3EE). scripts/gen-icons.mjs uses apps/web/node_modules/sharp to rasterize 2 master SVGs. flutter_launcher_icons v0.14.4 (dev dep) regenerates Android legacy+adaptive / iOS full set / Flutter web + manifest. React web: src/app/icon.svg + apple-icon.png + manifest.ts + public/icon-*.png (Next file-based conventions).
Fixed pbxproj ASSETCATALOG_COMPILER_GENERATE_SWIFT_ASSET_SYMBOL_EXTENSIONS=AppIcon bug (reverted — flutter_launcher_icons 0.14.4 mangles it). Fixed flutter-create default name/description in web/index.html + web/manifest.json.
Verified: flutter analyze 0, flutter build web --release OK (after clearing a STALE .dart_tool/flutter_build web_plugin_registrant still referencing the removed flutter_tts — pre-existing, unrelated), flutter test 903. apps/web npm run build OK (/icon.svg /apple-icon.png /manifest.webmanifest routes), typecheck clean, npx vitest run 795/795.
Commit b5f757f (57 files).
# SP-8 COMPLETE.

# ============================================================
# POST-DEVICE-TEST PUNCH LIST: SP-1..SP-8 ALL COMPLETE.
# SP-1 c27cdcd, SP-2 a33d16f, SP-3 608a785, SP-4 cec92ca, SP-5 9709123..df99778,
# SP-6 dd64a5d..1b65df2, SP-7 803dbe2..a8d8be7, SP-8 b5f757f. All pushed except SP-8 (pushing now).
# Flutter 903 tests / analyze 0. Web 795 tests / typecheck clean. Both build.
# ============================================================

---
# dart format cleanup (ae3a0c0): repo-wide `dart format lib test` (118 files), + fixed the 3
# curly_braces_in_flow_control_structures lints the tall-style formatter's line-splitting
# exposed (listening_comprehension_provider.dart x2, part7_source.dart). analyze 0, 903 tests
# unchanged. Standing debt from SP-5..8 resolved.

---
# SM-2 practice mode toggle (Flashcard vs Trộn AI) — plan f620112, 6 tasks.
# Formula: shouldUseFlashcard = roll + aiRatio < 1.0 (fp-safe form shipped; naive `roll < (1 - aiRatio)` has a double-precision bug at aiRatio=0.7,roll=0.3 — see Task 1 note below). aiRatio=0.7 reproduces old 30/70 exactly.
# Not persisted; setup screen always defaults to Flashcard. progress_screen.dart quick-start permanently aiRatio:0.0.
Task 1: impl 855271c. SessionConfig.aiRatio + shouldUseFlashcard/drawSessionAiRatio in exercise_result.dart. 917 tests (+8), analyze 0.
  IMPLEMENTER CAUGHT: `roll < (1-aiRatio)` fp bug at aiRatio=0.7,roll=0.3 (1-0.7=0.300...04) -> fixed as `roll + aiRatio < 1.0` (0.3+0.7 rounds exactly to 1.0). PROPAGATED FIX to plan's Task 4 web formula (same bug would've hit TS) before dispatching Task 4.
  Review: Approved (spec ✅, quality Approved). Re-derived fp boundary math independently, confirmed correct (round-half-to-even lands 0.3+0.7 on exactly 1.0). complete (f620112..855271c).
Task 2: impl a97d63a. PracticeSessionState.aiRatio (required, copyWith passthrough, empty=0); startSession passes config.aiRatio; _pickExercise deleted, _generateAt calls shouldUseFlashcard(word, aiAvailable, aiRatio, _random.nextDouble()) directly. 920 tests (+3), analyze 0.
  Review: Approved (spec ✅, quality Approved, no findings). complete (855271c..a97d63a).
Task 3: impl 25e7c65. _PracticeMode{flashcard,mixed} enum (private), _mode default flashcard, _resolveAiRatio() = 0.0 or drawSessionAiRatio(Random().nextDouble()), BloomSectionHeader+BloomSegmented toggle inserted after word-count filter. Both _start()/_startDueSession() wired. 923 tests (+3), analyze 0.
  Review: Approved (spec ✅, quality Approved, no findings). complete (a97d63a..25e7c65). Flutter side DONE (Tasks 1-3), 923 tests, analyze 0.
Task 4: impl 52db31a. pickExercise.ts: shouldUseFlashcard(record, aiAvailable, aiRatio=0.7, rng?) [default 0.7 added by implementer so practice/page.tsx's still-2-arg call keeps typechecking until Task 5 rewires it — sensible interim], drawSessionAiRatio(rng?). Same fp-safe `rng()+aiRatio<1` formula as Flutter. 800 tests (+5 net: was 795, pickExercise 5->10 = +5), typecheck clean.
  Review: Approved (spec ✅ w/ 1 flagged deviation: aiRatio default=0.7 is interim, MUST be removed in Task 5). complete (25e7c65..52db31a).
Task 5: impl a095e9c. page.tsx: practiceMode state + aiRatioRef (set in both handleStart + auto-start effect), shouldUseFlashcard(word, aiAvailable, aiRatioRef.current), toggle via existing .chip-row/.vb-chip. pickExercise.ts's interim `=0.7` default REMOVED (confirmed only caller was page.tsx, already updated). 802 tests (+2), typecheck clean.
  Review: Approved (spec ✅, quality Approved, no findings). complete (52db31a..a095e9c). Web side DONE (Tasks 4-5). ALL 5 IMPL TASKS COMPLETE.
Task 6 (gate + docs): DONE (controller). flutter analyze 0 / test 923; web typecheck clean / vitest 802. README updated (Luyện tập cách khoảng section + roadmap checkbox).
# ALL 6 TASKS COMPLETE. Range 855271c..a095e9c + docs. Flutter 923 tests (was 909), web 802 (was 795). Whole-branch review next.

## SM-2 practice mode toggle whole-branch review (opus) — Ready: YES, no Critical. 2 Important + 5 minors.
I1 (process note, no code fix): my review-package base 952a510 was AFTER Task 1's impl 855271c — reviewer independently re-verified exercise_result.dart/progress_screen.dart/exercise_result_test.dart directly from cc581aa~1..f4647a0, all correct. Future review-package bases must be the spec commit's PARENT, not a mid-feature docs commit.
I2: web page.tsx "Về Ôn tập" (line ~350) and "Ôn tập lại ngay" (~353) do NOT reset practiceMode -> setup screen can re-open on Trộn AI, contradicts spec "always opens on Flashcard" + diverges from Flutter (which resets via full remount on every context.go back to /practice/vocab). FIX: reset practiceMode to "flashcard" on both.
Minors: M1 plan/ledger docs still show naive `roll < 1-aiRatio` in a few spots (code is correct, fp-safe form only propagated to web task snippet) - fix docs; M2 `[0.20,0.80]` vs `[0.20,0.80)` doc wording mismatch - fix; M3 practice_home_screen.dart uses fresh Random() per call vs provider's shared _random field - harmless, SKIP; M4 no "not persisted across Về Ôn tập/Ôn tập lại ngay" regression test - ADD one (this is what would've caught I2); M5 web toggle buttons have no aria-pressed/radio semantics (Flutter's BloomSegmented handles this) - ADD aria-pressed.
FIX WAVE: DISPATCHED (I2 + M1 + M2 + M4 + M5; M3 skipped).
FIX WAVE 16fc1c1: I2 fixed (handleStart gained explicit `mode` param to avoid async-setState stale-closure; also fixed a latent bug where onClick={handleStart} passed the click event as an arg) + both result buttons reset practiceMode. M1/M2 docs fixed. M4: 2 new regression tests (one would fail against the naive fix). M5: aria-pressed added. M3 skipped as planned. 804 tests (+2), typecheck clean.
FIX WAVE re-review: all FIXED (incl. both I2 sub-bugs independently re-derived), no regressions. Ready YES.
# SM-2 PRACTICE MODE TOGGLE COMPLETE. Range 855271c..16fc1c1 on master. Flutter 923 tests (was 909), analyze 0. Web 804 tests (was 795), typecheck clean.

---

# Knowledge Notes (Kiến thức) — Flutter Plan

**Plan:** docs/superpowers/plans/2026-09-07-knowledge-notes-flutter.md
**BASE commit (plan start):** 09a906b
**Branch:** master (per user)

## Status

- Task 1: ✅ complete (commit 1c10f35, 4/4 tests, review clean)
- Task 2: ✅ complete (commit 4ea4c69, 15/15 tests, review clean)
- Task 3: ✅ complete (commits 7ff04e9..d75943c, 4/4 tests, review clean — 1 Important fixed: textScaler regression)
- Task 4: ✅ complete (commits 416492a..21296a8, 7/7 tests, review clean — Minors: taxonomy test-strengthening applied)
- Task 5: ✅ complete (commit a538a7f, 5/5 tests, review clean — Minor: one misleading test comment inherited from brief (thi is a stopword))
- Task 6: ✅ complete (commit b9f7f6a, 9/9 tests, review clean)
- Task 7: ✅ complete (commit 3cea979, 4/4 tests, review clean)
- Task 8: ✅ complete (commit b1f4d23, analyze+971 clean, review clean)
- Task 9: ✅ complete (commit 34ad62a, 3/3 tests, review clean)
- Task 10: ✅ complete (commit fd3c467, 4/4 tests, full suite 978, review clean)
- Task 11: ✅ complete (commits 8ae9c31..6e30e82, 6 tests, full suite 981, review clean — 1 Important fixed: edit-mode origin/createdAt fallback)
- Task 12: ✅ complete (commit 25892ee, 10 tests, full suite 991, review clean)
- Task 13: ✅ complete (commit c75dc74, 3 tests, full suite 994, review clean)
- Task 14: ✅ complete (commits 8e45a63..944d66e, 7 tests, full suite 1001, review clean — 1 Important fixed: extend() request loss on Layer-2 path)
- Task 15: ✅ complete (commits f01e9af..4632184, 7 tests, full suite 1008, review clean — 1 Important fixed: /knowledge tab alias)
- Task 16: ✅ complete (commits 8f23614..4eec8f9, 2 new tests, full suite 1010, review clean — 3 Minor translation tweaks applied)
- Task 17: ✅ complete (commit 36ef02c, docs, full suite 1010, review clean)

## Minor Findings (for final review)

- Task 2 (Minor): bold_markup_test.dart could assert `expect(vectors, hasLength(14))` to guard the shared fixture contract against silent truncation.
- Task 2 (Minor): bold_markup.dart:44 has an unreachable `runs.isEmpty` fallback branch (harmless, defensive).

- Task 6 (Minor, for Task 9): KnowledgeNotesService.all() returns `const []` on empty/error paths — the Task 9 notifier MUST copy (`[...list]`) before mutating, or it throws on the empty case.
- Task 6 (Minor): seed path does two full-collection get()s (one redundant).
- Task 8 (Minor, follow-up chore): listening_comprehension_provider.g.dart + practice_session_provider.g.dart carry stale provider hashes — a clean `build_runner build` should be run once and the legit regen committed so future diffs stop surfacing this.
- Task 12 (Minor): KnowledgeDetailScreen BloomAppBar title is always '' (vocab_detail shows the headword) — echo note.title.
- Task 12 (Minor): group-screen row-tap test is weak (title on screen before+after nav); noteFixture carries redundant group+groupId alias.
- Task 13 (Minor, fold into Task 14): empty-state shows 3 AI/write buttons (centered 'Nhờ AI soạn' + bottom row's two). Task 14 should suppress the bottom row (or its AI button) in the empty branch.

## Whole-branch review (opus) — verdict: With fixes

FIX BATCH — landed in d270504, re-verified (opus review → 'ready to merge: Yes'), full suite 1022 green: C#1 swallowed write errors in upsert/delete; I#2 no aiAvailable gate in AI sheet; I#3 unvalidated suggestedGroupId; I#4 non-defensive DateTime.parse empties whole list (web-plan landmine); I#5 README over-promises (reworded); m#6 Bổ sung always rewrites source->ai (spec: unchanged unless starter); m#7 stopwords eat "thi"/"the".

FOLLOW-UPS (not gating this branch — for a later chore):
- #8 retire private _HighlightedText in reading_session_screen.dart, adopt shared widget w/ style param.
- #9 HighlightedText misses multi-word terms across double-space/newline (single-word headwords unaffected).
- #10 HighlightedText per-char regex perf — fine at current vocab sizes.
- #11 dead code: KnowledgeFilter.isActive, KnowledgeNote.copyWith(clearCefr) still unused after fix batch.
- #12 _KnowledgeEditRoute not-found returns blank "Ghi chú mới" (silent); detail screen shows "not found" on provider error state too.
- #13 restore snackbar always claims success — make it "Đã khôi phục N" / "Không có gì để khôi phục".
- #14 _knowledgeHasStarter hardcodes English vs asset-driven library; seedIfNeeded sets flag even for no-starter langs (spec-correct but means a future starter_zh never seeds existing accounts).
- #15 spec/plan flaw: starter_en_comparatives filed under en_articles_nouns — odd for browsing.
- #16 sheet→router seam tested in halves (assert lastPushedExtra type).
- #17 knowledge_note_source prompt interpolates Map.toString() not jsonEncode for extendingNote.
- Task 8: 2 stale .g.dart provider hashes (listening/practice) — clean build_runner + commit.

---

# Knowledge Notes (Kiến thức) — WEB Plan

**Plan:** docs/superpowers/plans/2026-09-09-knowledge-notes-web.md
**BASE commit (plan start):** 317ff54
**Branch:** master
**Web test baseline:** 804 pass (occasionally 1 async-media flake — re-run before assuming regression)

## Status
- Task 1: ✅ complete (commit e5ffff2, 4 tests, suite 808, review clean)
- Task 2: ✅ complete (commits d6a32ed..ec2f639, 16 tests, suite 824, review clean)
- Task 3: ✅ complete (commit a4686e9, 3 tests, suite 827, review clean)
- Task 4: ✅ complete (commits 0ba2149..4ce73fc, 8 tests, suite 835, review clean — 2 Minor hardening fixes)
- Task 5: ✅ complete (commits d888db6..c6c7ed2, 9 tests, suite 844, review clean — 1 Minor: filter-before-parse)
- Task 6: ✅ complete (commit d21d9c7, 3 tests, suite 847, review clean)
- Task 7: ✅ complete (commit 8e4eb50, 6 tests, suite 853, review clean)
- Task 8: ✅ complete (commit d45bf57, 4 tests, suite 857, review clean)
- Task 9: ✅ complete (commit 66b4574, 5 tests, suite 862, review clean)
- Task 10: ✅ complete (commits a3c8734..2ab9984, 4 tests, suite 866, review clean — 1 Important test-coverage gap closed + 2 Minor)
- Task 11: ✅ complete (commits c47b252, 4cc6651, 11 tests, suite 877 (2 pre-existing unrelated flakes — vocab-bank pagination + reading/part7 — both pass in isolation), review fixed — `use(params)`+Suspense hangs in this Vitest/jsdom/React 19 harness (verified via isolated repro), so a `useRouteParams` effect-based unwrap (`src/lib/useRouteParams.ts`) is used instead for all 3 dynamic-route pages; 1 Important fixed: hook didn't reset on `params` identity change (stale note under a new URL), now resets synchronously + regression test added)
- Task 12: ✅ complete (commit 15e77b7, 3 tests, suite 880, review clean)
- Task 13: ✅ complete (commits 0930ed4..cefd265, 5 tests, suite 885, review clean — 1 Important test-strengthening fix, mutation-verified)
- Task 14: ✅ complete (commit 886683e, 1 test, suite 886, build succeeded, review clean)

## Minor Findings (for final review)
- Web Task 12: `.btn-secondary` on an anchor link (Tự viết) is missing the `background: var(--surface)` fill every button sibling has (bloom.css:2463-472 scoped rule incomplete). Cosmetic.
- Web Task 12: `knowledge/new/page.tsx` loads the full per-language notes list for `existingNotes` though it's provably unused on the blank-new save path (no initial/overwriteNoteId to match) — harmless extra Firestore read, could pass [] instead.

## Whole-branch review (opus) — Web plan — verdict: With fixes

FIX BATCH — landed in cb52d66, verified directly by controller (Sửa link absolute, getVocabRecords .catch guard, useRouteParams render-phase reset + rejection handler), 890/890 tests, typecheck clean, build succeeded: C#1 KnowledgeNoteView "Sửa" link uses relative href "./edit" -> resolves to /knowledge/note/edit (edit page unreachable from UI, test only echoed the broken string); I#2 detail page Promise.all has no .catch on getVocabRecords -> one failed vocab fetch bricks the whole page forever; I#3 useRouteParams: reset to loading happens in a passive effect (not synchronous — one stale-content commit possible before the effect fires) + params.then has no .catch (rejected promise = permanent "Đang tải…", unhandled rejection) — patched in place (kept the hook per reviewer's sanctioned fallback), full useParams() migration logged as follow-up.

FOLLOW-UPS (not gating merge):
- I#4 (plan flaw): AiComposeModal Layer-2 "Vẫn tạo mới" discards the already-generated draft and calls the LLM a second time instead of reusing it (Flutter reuses); costs 2x BYOK calls + user may review a different note than the dedup warning was about. Needs a small state-machine change (carry draft/sourcePrompt in the Layer-2 related state, go straight to ready on proceed-new) — do as a follow-up commit, not blocking merge.
- Migrate the 3 dynamic-route pages off useRouteParams to Next's documented `useParams()` hook (sync, no Suspense, already works in this harness) and delete useRouteParams.ts + its test — removes the whole class of staleness/rejection risk instead of patching around it.
- m5 EditKnowledgeNoteModal draft-review header still says "Ghi chú kiến thức" instead of "Xem lại bản nháp" (only the aria-label has the right string).
- m7 knowledgeNoteSource prompt dropped "Vietnamese-friendly" from the tags instruction (web-generated notes may accumulate English tags).
- m8 tag input has no Enter-to-add (button-only; Flutter hint says "nhấn Enter").
- m10 restoreStarters keeps an unused `language` param (void language;).
- m11 knowledgeStarters.ts hardcodes `language === "english"` vs Flutter's asset-driven startersFor — a future starter_zh.json would only light up on mobile.
- m12 knowledge pages don't setNotes(null) on targetLanguage change — brief flash of the previous language's notes until refetch resolves.
- m14 test-quality nits: KnowledgeNoteView.test.tsx asserted the literal (broken) href string instead of route behavior; a couple of test titles/comments slightly mismatch what they assert.
- m15 stale eslint-disable react-hooks/exhaustive-deps on a complete dep list (knowledge/page.tsx).
- (carried from Task 12) .btn-secondary on an anchor missing background fill; knowledge/new/page.tsx loads an unused existingNotes list.

## English Interview Practice (plan docs/superpowers/plans/2026-09-27-english-interview-practice.md, branch feat/english-interview, base 4104717)
Task 1: complete (commits 4104717..77cf8ea, review clean)
- minor T1: functions/.env.example lacks STT_SERVICE_URL; pingCloudRun http branch doesn't check res.ok; no test for all-URLs-unset warmUp.
Task 2: complete (commits 77cf8ea..0cf7b28, review clean)
- minor T2: splitSentences can emit >maxLen chunk for a single token longer than maxLen; two near-identical packing loops; combinedAnswer (interviewTypes.ts) has no direct test.
Task 3: complete (commits 0cf7b28..00a6e37, review clean)
- minor T3: parseJson swallows the underlying parse error/raw text (no log); str/strList/parseJson generic utils live in interviewPrompts.ts.
Task 4: complete (commits 00a6e37..d5a8594, review clean)
- note T4: parseReport silently yields empty questions[] if AI garbles every mainIndex (by design; final review may decide).
Task 5: complete (commits d5a8594..dd7ee90, review clean)
- minor T5: listRecent over-fetch 20 then filter may return < max if many in_progress drafts; Firestore rules check deferred to Task 15 manual step.
Task 6: complete (commits dd7ee90..e385ce4, review clean) — pdfjs worker via new URL() bundles fine under Turbopack; no mammoth shim/postinstall needed
- minor T6: PDFs >10 pages silently truncated to first 10 (no user signal).
Task 7: complete (commits e385ce4..ae27d3c incl. 2 fixes: reentrant start busyRef + latch reset on MediaRecorder setup failure; review clean)
- minor T7: seconds (round) vs elapsed (floor) differ ≤1s; setup-failure catch doesn't clear timerRef (unreachable); cancel() during pending getUserMedia still starts recording afterwards.
Task 8: complete (commits ae27d3c..e9f4f3f, review clean)
Task 9: complete (commits e9f4f3f..3389f89 incl. fix: new playback supersedes in-flight one; review clean)
- minor T9: prefetched clips keep voice at prefetch time; unplayed prefetch entries never swept.
Task 10: complete (commits 3389f89..3adb976 incl. fix: stray `}` in bloom.css; build + postcss parse verified)
Task 11: complete (commits 3adb976..26d7ba0, review clean)
- minor T11: .iv-page class has no CSS rule (dead class). Full suite shows jsdom "HTMLMediaElement play/pause not implemented" noise traced to useInterviewAudio.test.ts (T9) — test output not pristine; final review to triage.
Task 12: complete (commits 26d7ba0..0113364, review clean)
- minor T12: SessionThread uses array index as key.
Task 13: complete (commits 0113364..6f255e3 incl. 2 fixes: stale-continuation guards, End disabled in transcribing, StrictMode-safe unmount flag, mic release after End; review clean)
- minor T13: pending-start race also exists for Skip/Replay (mic prompt open → orphan recorder, next start blocked until reload) — generalize guard via phase snapshot; End during recording drops the in-progress answer; tests cover happy path mostly (no reviewTranscript:false, 180s auto-stop, PLAN_FAILED retry tests); page.tsx ~450 lines.
Task 14: complete (commits 6f255e3..e4e425d incl. fix: phrase-save errors surfaced; review clean)
- minor T14: redundant capitalizeHeadword before lookup; second @media(max-width:980px) block could merge.
Task 15: complete (commit e4e425d..d42955a, docs + .env.example; functions 80/80, web build ok)
- flaky: interview/[id]/page.test.tsx "generates and saves the plan" asserts AUDIO.playPrefetched immediately after findByText — passive-effect race under full-suite load (failed once, passed 3/3 isolated + full 1094/1094 rerun). Needs waitFor.

Post-merge follow-up (2026-09-28, user-reported): "Dịch sang tiếng Việt" was a fresh `callInterviewAi` round-trip on every click (`buildTranslatePrompt`/`parseTranslation`), never cached. User asked to prepare the translation alongside question generation instead. Implemented:
- `buildQuestionPlanPrompt`/`parseQuestionPlan`: AI now returns `{"questions": [{"en", "vi"}]}` instead of `["..."]` — `InterviewSession.plan`/`InterviewState.plan` retyped `InterviewPlanItem[]` (new type in interviewTypes.ts).
- `buildNextTurnPrompt`/`parseNextTurn`: `follow_up` branch also returns `"vi"` (lenient — defaults to `""` if the AI omits it, doesn't throw).
- `InterviewState` gained `questionVi`, threaded through by `askMain` (from `plan[i].vi`) and the `FOLLOW_UP` event (`event.vi`) — travels with `question` regardless of whether it's a main or follow-up question.
- `handleTranslate` (page.tsx) now just displays `state.questionVi` — instant, no AI call — falling back to the old on-demand call only when it's empty.
- Backward compat: `interviewSessions.ts`'s `getInterviewSession` normalizes a legacy `plan: string[]` (sessions saved before this change) to `{en, vi: ""}[]`, so an in-progress session isn't broken by this change; its remaining questions just fall back to on-demand translate.
- Also fixed the same day: `.iv-session`'s forced `min-height: calc(100vh - 64px)` + `.iv-session-body`'s `flex: 1` left the short side-column's leftover space as dead air while pushing the sticky dock past the fold on shorter viewports (needed a scroll to reach it, per user screenshot). Removed both — layout now sizes to natural content height.
- web 1103 → 1107 tests (4 new: 2 in page.test.tsx for instant main/follow-up translate with no extra AI call, 1 legacy-plan-normalization case in interviewSessions.test.ts, 1 vi-defaults-to-empty case in interviewPrompts.test.ts), typecheck clean.

## Conversation Practice (2026-10-09, branch feat/conversation-practice)
Plan: docs/superpowers/plans/2026-10-09-conversation-practice.md (12 tasks, SDD). Base: 7ca5b4c
Task 1: complete (commits 7ca5b4c..580041a, review clean)
Task 2: complete (commits 580041a..c5858de, review clean). Minors: reply prompt JSON template omits suggestEnd in roleplay (page ignores it there); prompt text interpolation unescaped (BYOK low risk).
Task 12 note: spec §7 file-structure bullet for conversationHistory.ts ('returns the window to send (last 8)') is stale; fix to 'unsummarized window'.
Task 3: complete (commits c5858de..c9697aa, review clean)
Task 4: complete (commits c9697aa..2a4245b, review clean). Minor: session tests use expect.anything() for refs; never undefined hint.
Task 6: complete (commits 6ed5235..04321b3, review clean). Minors: score() coerces null/''→0; numeric-string messageIndex dropped; hasGoals must equal goals.length>0 in caller.
Task 5: implemented 6ed5235, review found stranded recording/sttError → fix 6474418 (CANCEL_RECORDING, DISMISS_STT_ERROR, canSend) — re-review pending
Task 5: complete after fix (6ed5235 + 6474418, re-review clean)
Task 7: complete (commit c32aad4, review clean)
Plan amended (uncommitted): Tasks 9/10 use CANCEL_RECORDING, DISMISS_STT_ERROR, canSend.
Task 8: complete (commits 6474418..1d63137, review clean). Minors: handleBuildScenario in-flight result can overwrite newer selection (disable tabs/cards while building); mode-switch test doesn't assert persona/goals reset.
Task 9: complete (commits 1d63137..dffa63c, review clean). Minors for polish: AI bubble surface-2 on surface may be low contrast; 'Bỏ qua, trả lời luôn' label wrong when state.final; double thinking indicator (thread + dock); .cv-link ~26px target; aria-labels per message; .cv-col min-width:0/overflow-wrap; tts_failed untested.
Task 10: implemented 320ac8d; opus review: Needs fixes (handleEnd drops segments while recording/sttError) + minors → fix dispatched (flush, resume-final→END, final closing delay when speakAloud off, stale suggestions). Deferred minors: handleStop/cancel race in useRecorder (stoppingRef stuck), no in-flight guard on translate/hint, state-closure reads in handleSend/End.
Task 11: complete (commit bd8ec5e, review clean). Minors: duplicate keys if AI repeats messageIndex/phrase text; delta 0 label; saved set not prepopulated.
Task 10: complete after fix (320ac8d + 557516e, re-review clean).
Polish pass: e9c8fc6 (Tasks 8/9/11 minors) done.
Task 12: complete (commit ee2dd12; manual verification step 4 pending with user).

## Mobile responsive web (2026-10-10, branch feat/mobile-responsive)
Plan: docs/superpowers/plans/2026-10-10-mobile-responsive-web.md (9 tasks, SDD). Base: 560de8e
Mobile Task 1: complete (560de8e..3bbbf38, review clean)
Mobile Task 2: complete (3bbbf38..b78d88b, review clean). Minors for later: .main bottom padding applies on session routes where tab bar hidden (~80px dead space) → fix in Task 7; a11y polish: aria-current on active links, icon aria-hidden in sheet links, focus assertions in tests, aria-modal no trap.
Mobile Task 3: complete (b78d88b..f7019c0, review clean). Mobile Task 4: implemented e10dfa3; found desktop regression (12px floor active on desktop) → fix dispatched (--type-min var).
Mobile Task 4: fix 8da04a7 (floor only on phones). Review: Needs fixes → (a) wrap originals <15px (not 13.5) so fs-small phone stays ≥12px, (b) .app-frame { font-size: calc(16px * var(--type-scale)) } so unstyled text follows scale, (c) anchor convention-test regexes. Dispatch AFTER Task 5 commits (same file).
Mobile Task 4: complete after fixes (e10dfa3, 8da04a7, 68f87a5); re-review folded into final whole-branch review. Mobile Task 5: implemented f729aa4 (audit only covers signed-out states — real layouts need iPhone check); review pending.
Mobile Task 5: complete after fix (f729aa4 + b6359aa; detector fixed, modal sheet above tab bar, min-width fix). Tasks 6-9 = code-review passes (audit sees only signed-out pages); iPhone feedback loop is the real check.
Mobile Task 6: implemented c45741d; review found Critical: phone .pron-btn{position:relative} defeats .selection-speak-btn{position:fixed} (reading selection button) → fix: scope with :not(.selection-speak-btn) or re-assert fixed + keep 26px; Minor: .lookup-sentence-original flex 1 1 0. Dispatch AFTER Task 7 commits (same file). Device-check list also: reading/listening/knowledge toolbars (.practice-filters/.vb-toolbar rules apply there).
Mobile Task 6: complete after fix (c45741d + 214598e). Task 7: implemented f7c6497 (sticky dock fix via :has overflow), opus review pending.
Mobile Task 7: complete (c45741d..f7c6497, opus review clean). Minors: button.btn-primary margin-top 4px in composer rows; mic order -1 vs DOM; dock overflow clips pulse ring; loading/error states of interview page lack .iv-session so keep 80px padding. Device checks: sticky dock w/ overflow:clip on Safari, dock height with iOS keyboard (50dvh), goal checklist reachability.
Mobile Task 8: complete (214598e..1171c07, opus review clean). Follow-ups: Nghe hiểu audio controls scroll away on phones (could add compact play/stop in sticky bar); wide content on 5 session pages clipped not scrollable; .modal-field .link-btn 44px also hits EditVocabModal; device checks: popover static position on iOS, selection speak 🔊 on long-press, sticky Nộp bài bar with overflow clip.
Mobile Task 9: complete (5fe5b2b). 0 FAIL at 414/375; desktop computed styles identical to baseline; build ok in shadow copy. Next: final whole-branch review.
Mobile feature: ALL TASKS COMPLETE + final review fixes (50b5fad, 3ac272e, 4daf4b9) on feat/mobile-responsive. Not merged/deployed.
Mobile responsive + Conversation/STT work: docs synced (README, specs, knowledge spec) and merged to master 2026-10-11.

## Conversation "Tại sao?" explanations (2026-10-19, direct on master)
Small change, no plan (brainstormed in chat; a separate sentence-building drill feature was considered and deferred until this is tried).
- Suggest options → {text, why[]} with collapsed "Tại sao?" toggle; hint + report corrections get why[] per edit; recurring mistakes get a one-line rule. Shared WHY_RULES/parseWhy in conversationPrompts.ts, WhyList component. Old hints/reports render unchanged; parser writes rule ""/why [] (never undefined).
- Report prompt: likely STT mishearings (sound-alike nonsense words) are not counted as learner mistakes.
- Commit 0ea5fff. Docs synced (README, conversation spec). Manual check with a live AI key still pending with user.

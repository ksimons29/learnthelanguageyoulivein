# Bug Findings - Session 2026-01-21

## ✅ FIXED: Finding #18: Bingo Squares Not Tracking (Issue #78)

### Status: **FIXED** (Session 66 - 2026-01-22)

### Observed Behavior
1. User completes 18 reviews with fill-blank and multiple choice exercises
2. User finishes daily session (daily goal complete)
3. Bingo board shows **0/9 completed** instead of expected 4+/9

### Root Cause
Exercise type format mismatch between client and API:
- Client sends: `'fill_blank'` (underscore)
- API expected: `'fill-blank'` (hyphen)

The comparison `data.exerciseType === 'fill-blank'` never matched `'fill_blank'`, so `fillBlank` and `multipleChoice` squares were never tracked.

### Fix Applied
Normalize exerciseType by replacing underscores with hyphens before comparison:
```typescript
const normalizedExerciseType = data.exerciseType?.replace(/_/g, '-');
```

### Verification
- E2E verified: `squaresCompleted` went from `[]` to `["review5", "socialWord"]` after fix

### GitHub Issue: #78

---

## ✅ FIXED: Finding #17: Progress Page 500 Error (Issue #77)

### Status: **FIXED** (Session 67 - 2026-01-22)

### Observed Behavior
1. Navigate to Progress page
2. Page shows "Failed to fetch progress data"
3. Console shows 500 error

### Error Details
```
GET /api/progress => 500

Error: Failed query: select date("next_review_date"), count(*)::int from "words" ...
```

### Root Cause
PostgreSQL `date()` function incompatibility with Drizzle ORM's parameterized queries.

When using `sql`date(${words.nextReviewDate})`` Drizzle converts the column reference to a parameter placeholder like `date($6)`. PostgreSQL's `date()` function cannot accept parameterized column references.

### Fix Applied
Used `sql.raw()` for column names inside PostgreSQL `date()` function:
```typescript
// BEFORE (broken):
date: sql<string>`date(${words.nextReviewDate})`

// AFTER (fixed):
date: sql<string>`date(${sql.raw('next_review_date')})`
```

Changes made in `web/src/app/api/progress/route.ts`:
- Streak query: `date(${reviewSessions.endedAt})` → `date(${sql.raw('ended_at')})`
- Forecast query: `date(${words.nextReviewDate})` → `date(${sql.raw('next_review_date')})`
- Activity heatmap: `date(${reviewSessions.endedAt})` → `date(${sql.raw('ended_at')})`

### Verification
- ✅ Build passes
- ✅ 231 unit tests pass
- ✅ EN→PT test user: Progress page loads correctly
- ✅ EN→SV test user: Progress page loads correctly
- ✅ NL→EN test user: Progress page loads correctly

### GitHub Issue: #77

---

## ✅ FIXED: Finding #16: Gamification Daily Goal Always Shows 0/10

### Status: **FIXED** (Session 66 - 2026-01-22)

### Observed Behavior
1. User completes 18 reviews in a review session
2. Review completion screen shows "18 words reviewed, 83% accuracy"
3. Dashboard shows "0/10 Daily Goal" - reviews not counting!
4. Streak stays at 0 even after completing daily goal

### Root Cause
**Missing database unique index!** The Drizzle schema defines:
```typescript
uniqueIndex('daily_progress_user_date_idx').on(table.userId, table.date)
```

But this index **was never created in the production database**. This caused:
1. Multiple `daily_progress` records created for the same user/date (race condition)
2. Reviews scattered across duplicate records instead of accumulating in one
3. When UI fetches state, it gets a random record (often one with 0 reviews)

### Evidence
```sql
-- Before fix: 8 duplicate records for EN→SV user on 2026-01-22
SELECT user_id, date, COUNT(*) FROM daily_progress GROUP BY user_id, date HAVING COUNT(*) > 1;
-- Result: 6 user/date combinations with duplicates, up to 44 duplicates each!
```

### Fix Applied
1. Created `scripts/fix-gamification-duplicates.ts`
2. Consolidated duplicate records (summed completed_reviews)
3. Added missing unique index: `daily_progress_user_date_idx`
4. Added missing unique index: `bingo_state_user_date_idx`
5. Fixed `completed_at` for records that exceeded target but weren't marked complete
6. Updated streak state for affected users

### Verification
- Dashboard now shows **18/10 Goal Complete!**
- Streak now shows **1 Day Streak**
- Unique index prevents future duplicates

### Prevention
- Run `npm run db:push` after schema changes to ensure indexes are created
- Add integration test for gamification state consistency
- Consider adding a health check that verifies schema indexes exist

---

## Critical Issue: Recurring Bugs That Were "Fixed"

This document tracks bugs discovered during user testing that appear to be regressions or incomplete fixes. The goal is to:
1. Document each issue with evidence
2. Identify root causes
3. Establish guardrails to prevent recurrence
4. Ensure MVP-level quality before release

---

## Finding #1: Sentence Page Shows Portuguese Words Instead of English Translations

### Screenshot Evidence
- **Location:** Review tab → Sentence generation view (llyli.vercel.app)
- **Time:** 17:08

### Observed Behavior
1. Sentence page shows a list of words to select for sentence generation
2. Words displayed: tampo, convite, peça, água, volante, precisar, Intemporal, feira de emprego, Trainwreck
3. **"Trainwreck" shows correctly in English** (user's native language)
4. **All other words show in Portuguese** - but user needs to see ENGLISH translations to select words they want to practice
5. Footer shows "2 words in this sentence" - selection counter working

### Expected Behavior
- Word list should show **English translations** (user's native language) so they can select words they want to include in a practice sentence
- Portuguese is the target language - user is learning Portuguese, so they need to see words in a language they understand to make selections

### The Core Problem
**Language direction confusion:** The sentence word picker shows target language (Portuguese) instead of native language (English). User can't meaningfully select words if they don't know what the Portuguese words mean.

### Root Cause Analysis
| Possible Cause | Likelihood | Investigation Needed |
|----------------|------------|----------------------|
| Wrong field displayed (phrase vs translation) | High | Check sentence word list component |
| Language direction not respected in query | High | Check how words are fetched for sentence UI |
| Display logic assumes wrong direction | High | Check component props/rendering |

### Why This Bug Exists
1. **Language direction complexity** - App supports multiple language pairs (EN→PT, EN→SV, NL→EN)
2. **Field naming confusion** - `phrase` vs `translation` meaning depends on direction
3. **No test for correct language display** - Tests may check data exists, not which language shows

---

## Finding #2: System KNOWS Translations But Doesn't Display Them

### Screenshot Evidence
- **Location:** Review tab → Sentence generation (llyli.vercel.app)
- **Time:** 17:13

### Observed Behavior
1. Word list still shows Portuguese: peça, água, volante, precisar, Intemporal, feira de emprego, Trainwreck
2. "precisar" is selected (coral highlight with X to deselect)
3. **Bottom shows: "apontado: pointed | peça: piece"** - the system KNOWS the English translations!
4. "Not quite" feedback shown at bottom

### The Irony
The explanation bar at the bottom correctly displays `portuguese: english` format, proving:
- The translation data EXISTS in the database
- The system CAN format it correctly
- The word LIST component just doesn't use the right field

### Root Cause
This is a **display logic bug**, not a data bug. The word picker component is showing `word.phrase` (Portuguese) instead of `word.translation` (English), while the explanation component correctly shows both.

### Fix Complexity
Should be simple - change which field the word list displays. But needs test to prevent regression.

---

## Finding #3: Duplicate Words in Review Queue + No Shuffling

### Screenshot Evidence
- **Location:** Review tab (llyli.vercel.app)
- **Time:** 17:15

### Observed Behavior
1. Word list shows: Intemporal, volante, água, precisar, feira de emprego, tampo, peça, Trainwreck
2. **"apontado" appears twice in the review queue** (user confirmed)
3. Word order appears similar across sessions - no shuffling

### Expected Behavior
- Each word should appear ONCE per review session
- Words should be shuffled/randomized to prevent memorizing order
- If user has limited vocabulary, system should still avoid immediate duplicates

### The Problem
1. **Duplicate insertion:** Same word added to queue multiple times
2. **No deduplication:** Query or queue logic doesn't filter duplicates
3. **No shuffle:** Words always appear in same order (likely insertion order or alphabetical)

### Root Cause Analysis
| Possible Cause | Likelihood | Investigation Needed |
|----------------|------------|----------------------|
| Review queue query lacks DISTINCT | High | Check review queue SQL |
| Multiple FSRS cards for same word | Medium | Check card creation logic |
| Queue populated multiple times | Medium | Check when queue is built |
| No randomization in ORDER BY | High | Check query ORDER clause |

### Why This Is Bad for Learning
1. **Primacy/recency bias** - User memorizes position, not word
2. **Duplicate reviews waste time** - User sees same word back-to-back
3. **Predictability reduces engagement** - Learning feels mechanical

### Proposed Guardrails
1. **Database constraint:** Unique index on (user_id, word_id) in review queue
2. **Query fix:** Add `DISTINCT` and `ORDER BY RANDOM()` or shuffle in code
3. **Test:** Assert review queue has no duplicate word_ids
4. **Test:** Assert word order differs between sessions (statistical test)

---

## Finding #4: Fill-in-the-Blank Shows WRONG Word as Target

### Screenshot Evidence
- **Location:** Review tab → Sentence exercise (llyli.vercel.app)
- **Time:** 17:19

### Observed Behavior
1. Sentence shown: "Além disso, os **[Observadores]** vão fazer um relatório."
2. "Observadores" is highlighted in teal as the blank to fill
3. Hints shown: "além disso: besides | Observadores: Watchers"
4. User presumably answered based on highlighted word
5. **Error feedback: "Not quite - The answer was: além disso"**

### The Critical Problem
- **Visual highlight:** "Observadores" (user thinks this is what to translate)
- **Expected answer:** "além disso" (completely different word!)
- **Result:** Exercise is IMPOSSIBLE to complete correctly

The user sees "Observadores" highlighted, logically answers "Watchers", and gets marked wrong because the system expected "besides" (for "além disso" which ISN'T highlighted).

### Why This Is a P0 Showstopper
1. **Core feature is broken** - The main learning exercise doesn't work
2. **User frustration** - Correct answers marked wrong
3. **Trust destroyed** - User can't rely on the app to work
4. **Learning impossible** - Can't learn if feedback is wrong

### Root Cause Analysis
| Possible Cause | Likelihood | Investigation Needed |
|----------------|------------|----------------------|
| Highlight index ≠ answer index | **Very High** | Check how currentWordIndex is used |
| Multiple words selected, wrong one highlighted | High | Check sentence word selection logic |
| State desync between display and validation | High | Check answer validation vs display state |
| Array indexing off-by-one | Medium | Check 0-based vs 1-based indexing |

### Likely Code Bug
```typescript
// PROBABLE BUG: Something like this
const highlightedWord = sentence.words[visualIndex];  // Shows "Observadores"
const expectedAnswer = sentence.words[answerIndex];   // Expects "além disso"
// visualIndex ≠ answerIndex
```

### Why This Bug Exists
1. **Complex state:** Sentence has multiple words, each with index
2. **Separate concerns:** Display logic vs validation logic not in sync
3. **No integration test:** Unit tests may pass individually but integration fails
4. **Happy path testing:** Dev tested with single-word sentences?

### Required Test (MUST ADD)
```typescript
test('highlighted word matches expected answer', async () => {
  const sentence = await generateSentence(userId, [word1, word2]);
  const highlightedWordInUI = getHighlightedWord(sentence);
  const expectedAnswer = getExpectedAnswer(sentence);

  // THE CRITICAL ASSERTION
  expect(highlightedWordInUI.phrase).toBe(expectedAnswer.phrase);
});
```

### Proposed Guardrails
1. **Invariant check in code:** Assert highlighted word === expected answer before render
2. **Integration test:** Full flow from sentence generation to answer validation
3. **Visual regression test:** Screenshot comparison with known-good state
4. **Runtime assertion:** Throw error if mismatch detected (fail fast, don't confuse user)

---

## Finding #5: Multiple-Choice Options in WRONG Language + Wrong Answer

### Screenshot Evidence
- **Location:** Review tab → Multiple choice exercise (llyli.vercel.app)
- **Time:** 17:21

### Observed Behavior
1. Prompt: "Choose the correct meaning:"
2. Sentence: "Além disso, o **[excerto]** é muito interessante."
3. "excerto" is highlighted in teal (the word to translate)
4. **Answer options are ALL IN PORTUGUESE:** convite, tampo, precisar, Intemporal, Trainwreck, peça, além disso, Observadores
5. "Intemporal" is user's selection (coral highlight)
6. **"além disso" shows checkmark as correct answer**

### Multiple Bugs in One Screen

#### Bug 5a: Answer options in wrong language
- User must "choose the correct meaning" of "excerto"
- Options should be ENGLISH: "excerpt", "invitation", "lid", etc.
- Options ARE Portuguese: convite, tampo, precisar, etc.
- **User cannot succeed** - no English translations to choose from

#### Bug 5b: Wrong word marked as correct (same as Finding #4)
- Highlighted word: "excerto" (means "excerpt" in English)
- Marked correct: "além disso" (means "besides" in English)
- These are DIFFERENT WORDS with different meanings
- System expects answer for wrong word

#### Bug 5c: Confusing exercise flow
- "excerto" not even in the answer list
- "além disso" appears BOTH in sentence AND as an answer option
- Completely broken user experience

### Why This Is Worse Than Finding #4
This combines:
1. Wrong language in options (Finding #1 pattern)
2. Wrong word as expected answer (Finding #4 pattern)
3. Highlighted word absent from options entirely

### Root Cause Pattern
The entire sentence review feature has **pervasive state confusion**:
- Display component and validation component disagree on current word
- Language direction logic applied inconsistently
- Word index tracking broken across the flow

### The Common Thread
Every finding points to the same architectural problem:
```
[Word Selection] → [Sentence Generation] → [Display] → [Validation]
     ↓                    ↓                   ↓            ↓
   Index A             Index B            Index C       Index D

   A ≠ B ≠ C ≠ D  ← STATE DESYNCHRONIZATION
```

### Required Fix Approach
1. **Single source of truth** for current word in sentence
2. **Derive all other values** from that source
3. **Invariant assertions** at each step to fail fast
4. **Integration test** that traces full flow end-to-end

---

## Finding #6: Word Selection Limited + Portuguese Display (Again)

### Screenshot Evidence
- **Location:** Review tab → Word selection / Post-exercise (llyli.vercel.app)
- **Time:** 17:22

### Observed Behavior
1. Options shown: feira de emprego, além disso (selected), Observadores, precisar
2. **All options in Portuguese** - same bug as Findings #1, #5
3. Bottom hints: "além disso: besides | peça: piece" - translations exist but not shown
4. "Correct!" feedback displayed
5. "2 words in this sentence" shown
6. **User cannot add more words** - limited to 2 words only

### New Bug: Sentence Word Limit Too Restrictive

#### The Problem
- User says they cannot add more than 2 words to a sentence
- With limited vocabulary (new learners), sentences should support MORE words
- Practicing multiple words in context is the core value proposition

#### Why This Matters
- "Learning multiple words in context" is shown as feature tagline
- But limiting to 2 words defeats the purpose
- User should be able to select 3-5+ words for richer practice

### Confirmed Pattern
This is now the **4th screen** showing Portuguese instead of English translations:
- Finding #1: Word picker - Portuguese
- Finding #5: Multiple choice options - Portuguese
- Finding #6: Word selection - Portuguese

**This is not an isolated bug - it's a systemic language direction failure.**

### Root Cause Hypothesis
The entire sentence review feature has `phrase` and `translation` fields swapped:
- `phrase` = target language (Portuguese)
- `translation` = native language (English)
- Display logic uses `phrase` everywhere instead of `translation`

One-line fix potential, but needs comprehensive testing across all views.

---

## Finding #7: Correct Answer NOT in Options - Exercise Impossible

### Screenshot Evidence
- **Location:** Review tab → Sentence Review (llyli.vercel.app)
- **Time:** 17:23

### Observed Behavior
1. "SENTENCE REVIEW" header shown (coral badge)
2. "Choose the correct meaning:"
3. Sentence: "Além disso, preciso de **[selos]** para enviar cartas."
4. "selos" is highlighted in teal (means "stamps" in English)
5. **Options shown:** Trainwreck, além disso, convite, água, peça, Battery, feira de emprego, precisar, volante, tampo, Observadores, Intemporal
6. **"stamps" is NOT an option!**
7. User CANNOT complete the exercise correctly

### Multiple Issues in One Screen

#### Bug 7a: Correct answer missing from options
- Highlighted word: "selos" (Portuguese for "stamps")
- Expected correct answer: "stamps" (English)
- Available options: None contain "stamps"
- **Exercise is literally impossible**

#### Bug 7b: Options are mixed languages
- English words: Trainwreck, Battery
- Portuguese words: além disso, convite, água, peça, feira de emprego, precisar, volante, tampo, Observadores, Intemporal
- **No consistency** - should all be English translations

#### Bug 7c: Options are user's OTHER vocabulary, not distractors
- The options appear to be the user's entire word list
- They're not semantically related distractors (e.g., other nouns like "letters", "envelopes")
- This makes the exercise meaningless for learning

### Root Cause Analysis
| Possible Cause | Likelihood | Investigation Needed |
|----------------|------------|----------------------|
| Options populated from word list, not sentence context | **Very High** | Check how options are generated |
| Correct answer never added to options array | **Very High** | Check option generation logic |
| Field swap (phrase vs translation) in option display | High | Already confirmed pattern |

### Why This Is a P0 BLOCKER
1. **Exercise cannot be completed** - no valid answer exists
2. **User wastes time** - will try every option and fail
3. **Trust completely destroyed** - app is fundamentally broken
4. **Core feature non-functional** - sentence review is the main learning method

### The Correct Behavior
```typescript
// Options should be:
const correctAnswer = "stamps";  // Translation of highlighted "selos"
const distractors = ["letters", "packages", "envelopes", "postcards"]; // Related words
const options = shuffle([correctAnswer, ...distractors]);
```

### What's Actually Happening
```typescript
// Bug: Options are just user's other vocabulary
const options = userVocabulary.map(word => word.phrase); // Wrong field!
// AND correct answer never inserted
// AND mixed languages
```

---

## Finding #8: "Captured Today" Resets on Navigation

### Screenshot Evidence
- **Location:** Today page (llyli.vercel.app)
- **Time:** 17:25

### Observed Behavior
1. User captures words during session
2. User navigates to another tab (Review, Notebook, etc.)
3. User returns to Today page
4. **"Captured Today" section shows: "No phrases captured today yet"**
5. Previously captured words are gone from the list

### Expected Behavior
- "Captured Today" should persist across navigation
- Should show all words captured since midnight today
- Data comes from database (has `createdAt` timestamp), not just client state

### Root Cause Analysis
| Possible Cause | Likelihood | Investigation Needed |
|----------------|------------|----------------------|
| Client state reset on unmount | High | Check if using Zustand persist |
| Query not re-fetching on mount | High | Check React Query stale time |
| Date filter logic incorrect | Medium | Check timezone handling |
| Component fetches but shows stale | Medium | Check loading states |

### Impact
- User loses visibility into what they captured
- Feels like data loss (even if data is saved)
- Breaks the feedback loop of "capture → see → review"

---

## Finding #9: Inbox Count Mismatch - 4 Shown, None Visible

### Screenshot Evidence
- **Location:** Notebook page (llyli.vercel.app)
- **Time:** 17:25

### Observed Behavior
1. Notebook page shows: "Inbox - 4 new & untagged phrases"
2. User taps to open Inbox
3. **Only "other" category visible, not the 4 items**
4. The promised 4 phrases don't appear

### Expected Behavior
- Tapping Inbox should show 4 untagged phrases
- User can then organize/categorize them
- Count and content should match

### Root Cause Analysis
| Possible Cause | Likelihood | Investigation Needed |
|----------------|------------|----------------------|
| Category filter wrong in Inbox view | High | Check inbox query filters |
| "Untagged" definition mismatch | High | Count query ≠ display query |
| Items have category "other" but count excludes "other" | Medium | Check category logic |
| Stale count (not refreshed) | Medium | Check when count updates |

---

## Finding #10: Review Due Count Conflict Between Pages

### Screenshot Evidence
- **Location:** Notebook + Today pages (llyli.vercel.app)
- **Time:** 17:25

### Observed Behavior
1. **Notebook page shows: "DUE TODAY: 49"**
2. **Today page shows: "Review Due: 0 phrases waiting"**
3. Same user, same time, completely different counts!

### The Contradiction
| Page | Due Count |
|------|-----------|
| Notebook | 49 |
| Today | 0 |

This is the same data source - how can it show 49 on one page and 0 on another?

### Root Cause Analysis
| Possible Cause | Likelihood | Investigation Needed |
|----------------|------------|----------------------|
| Different FSRS due date calculations | High | Compare queries |
| Today page checks different criteria | High | Maybe includes "new" filter |
| Caching issue - stale data | Medium | Check cache invalidation |
| Timezone mismatch | Medium | Server vs client time |

### Why This Is Critical
- User sees 49 due, goes to review, sees 0
- Completely confusing and breaks trust
- Either Notebook is wrong or Today is wrong (or both!)
- **One source of truth needed**

### Required Fix
```typescript
// MUST use same function everywhere
const dueCount = calculateDueCards(userId, today);

// Notebook and Today pages both call this
// No separate implementations
```

### Fix Applied (Commit 8ee1fbe)

**Root Cause:** Today page calculated due count client-side (all words with `nextReviewDate <= now`), while Notebook fetched from `/api/words/stats` which applies FSRS scientific limits (max 15 new cards/day + review due).

**The Fix:**
1. Added server stats fetch to Today page (`/api/words/stats`)
2. Use `serverStats.dueToday` as single source of truth
3. Fall back to client-side calculation if API fails

**Files Changed:**
- `web/src/app/page.tsx` - Fetch due count from API
- `web/src/__tests__/lib/due-count.test.ts` - Unit tests for FSRS formula

**E2E Verification:**
- ✅ test-en-pt (EN→PT): Today=7, Notebook=7 ✓
- ✅ test-en-sv (EN→SV): Today=15, Notebook=15 ✓
- ✅ test-nl-en (NL→EN): Today=5 (Notebook had separate 500 error)

---

## Findings Summary

| # | Issue | Severity | Status |
|---|-------|----------|--------|
| 1 | Sentence page shows Portuguese instead of English translations | **P0 Critical** | Documenting |
| 2 | System knows translations but doesn't display them in word list | **P0 Critical** | Documenting |
| 3 | Duplicate words in review queue (apontado x2) | **P1 High** | Documenting |
| 3a | No shuffling - words appear in same order | **P1 High** | Documenting |
| 4 | Fill-in-blank highlights WRONG word - answer mismatch | **P0 BLOCKER** | Documenting |
| 5 | Multiple-choice options in Portuguese instead of English | **P0 BLOCKER** | Documenting |
| 5a | Wrong word marked as correct (excerto highlighted, além disso "correct") | **P0 BLOCKER** | Documenting |
| 6 | Word selection capped at 2 words - too restrictive | **P2 Medium** | Documenting |
| 6a | Portuguese display in word selection (4th occurrence) | **P0 Critical** | Documenting |
| 7 | **Correct answer NOT in multiple choice options** | **P0 BLOCKER** | Documenting |
| 7a | Options are user's other vocab, not related distractors | **P1 High** | Documenting |
| 7b | Mixed languages in options (Trainwreck, Battery vs Portuguese) | **P0 Critical** | Documenting |
| 8 | "Captured Today" resets when navigating away | **P1 High** | ✅ **VERIFIED WORKING** (Session 60) |
| 9 | Inbox shows 4 items but none visible when opened | **P1 High** | ✅ **FIXED** (commit ffef140) |
| 10 | **Due count conflict: Notebook=49, Today=0** | **P0 Critical** | ✅ Fixed (8ee1fbe) |

---

---

## META-ISSUE: Why Existing Guardrails Are Failing

### The Uncomfortable Truth

CLAUDE.md already contains:
- Mandatory `npm run build` and `npm run test:run` after every change
- E2E testing via Playwright MCP
- Test accounts with different language pairs (EN→PT, EN→SV, NL→EN)
- Comprehensive test scripts

**Yet bugs still ship. Why?**

### Guardrail Failure Analysis

| Guardrail | Status | Why It Failed |
|-----------|--------|---------------|
| `npm run build` | ✅ Runs | Only catches TypeScript errors, not logic bugs |
| `npm run test:run` | ⚠️ Runs | Tests exist but don't cover this scenario |
| Playwright E2E | ❌ Skipped? | Manual step easily forgotten under time pressure |
| Language pair testing | ❌ Not done | Tests likely only run for one language direction |
| Scale testing (500+ records) | ❌ Not done | Performance tested, not correctness |

### Root Causes of Guardrail Failure

1. **Tests verify presence, not correctness**
   - Test: "Does word list render?" ✅
   - Missing: "Does word list show the RIGHT language?" ❌

2. **Happy path bias**
   - Test with EN→PT user, see Portuguese words, assume correct
   - Never verified FROM USER PERSPECTIVE what language SHOULD show

3. **No user scenario tests**
   - PRD has user stories, but no automated tests trace full scenarios
   - "As a user, I want to select words I understand" ← not tested

4. **Build passes ≠ Feature works**
   - TypeScript catches type errors
   - Logic errors pass through silently

5. **Manual E2E is optional in practice**
   - CLAUDE.md says "also run E2E" but it's not enforced
   - Time pressure → skip manual testing → bugs ship

### What Must Change

1. **Semantic test assertions**
   ```typescript
   // BAD: Tests structure
   expect(wordList).toHaveLength(10);

   // GOOD: Tests meaning
   expect(wordList[0].displayLanguage).toBe(user.nativeLanguage);
   ```

2. **User scenario integration tests**
   - Not unit tests, not E2E, but scenario tests
   - "Complete sentence generation flow with EN→PT user"
   - Assert on user-visible outcomes

3. **Multi-language pair CI**
   - Every PR must pass tests for ALL language directions
   - Not just EN→PT

4. **Pre-commit hook for critical paths**
   - Changes to `/review`, `/sentence`, word display → force E2E

5. **Acceptance criteria as code**
   - PRD says "user sees words in their native language"
   - This must become an automated test, not a hope

---

## Action Items Before Fixing

- [ ] Add more screenshots to this document
- [ ] Trace the full user flow that triggers this
- [ ] Identify the specific commit that broke this (git bisect)
- [ ] Write the test FIRST that would catch this bug
- [ ] Then fix the bug
- [ ] Verify fix catches the test
- [ ] Add pre-commit hook for this file

---

## FINAL ASSESSMENT: Brutal Honesty

### The State of the App

**The sentence review feature - the app's differentiating feature - is 100% broken.**

Not edge cases. Not minor issues. The core flow fails at every step:
- Can't select words (wrong language shown)
- Can't complete exercises (wrong word highlighted)
- Can't answer questions (correct answer missing)
- Can't trust feedback (wrong answers marked correct)

**This is not MVP-ready. This is pre-alpha quality.**

### Bug Count Summary

| Severity | Count | Description |
|----------|-------|-------------|
| **P0 BLOCKER** | 5 | Core features completely broken |
| **P0 Critical** | 5 | Serious issues preventing normal use |
| **P1 High** | 4 | Significant problems affecting UX |
| **P2 Medium** | 1 | Minor limitations |
| **Total** | **15** | In a single 20-minute test session |

### Why This Happened - Honest Analysis

1. **"Fixed" without verification**
   - Bugs marked fixed in PROJECT_LOG without E2E validation
   - Code changes made, build passed, assumed working

2. **Tests check structure, not semantics**
   - "Does component render?" ✅
   - "Does it show the RIGHT content?" Never asked

3. **Happy path tunnel vision**
   - Tested EN→PT, saw Portuguese, assumed correct
   - Never asked "what SHOULD the user see?"

4. **Manual testing skipped under time pressure**
   - CLAUDE.md says "also run E2E" - optional language
   - Easy to skip when build passes

5. **No user-perspective testing**
   - Developer sees code working
   - User sees app failing
   - Gap never bridged

6. **Incremental changes without integration testing**
   - Each small change "worked"
   - Combined result: completely broken

### Mandatory Changes - Non-Negotiable

#### 1. Before ANY PR to sentence review feature:
```bash
# REQUIRED - not optional
npm run build
npm run test:run
# THEN: Manual E2E with Playwright MCP
# - Complete full sentence flow
# - Verify language direction
# - Verify highlighted word = expected answer
# - Verify correct answer in options
```

#### 2. New Test Requirements
```typescript
// MUST exist before feature ships:
test('word picker shows native language (English)', () => {
  expect(displayedWord.language).toBe(user.nativeLanguage);
});

test('highlighted word matches expected answer', () => {
  expect(highlightedWord.id).toBe(expectedAnswer.id);
});

test('correct answer exists in options', () => {
  expect(options).toContain(correctAnswer);
});

test('all options in same language', () => {
  const languages = options.map(o => o.language);
  expect(new Set(languages).size).toBe(1);
});

test('due count same across all pages', () => {
  expect(notebookDueCount).toBe(todayDueCount);
});
```

#### 3. Pre-Commit Hook for Critical Files
Any change to these files MUST include E2E validation:
- `app/review/**`
- `components/sentence/**`
- `lib/fsrs/**`
- `stores/review-store.ts`

#### 4. Definition of "Fixed"
A bug is NOT fixed until:
- [ ] Code change made
- [ ] Unit test added that would have caught the bug
- [ ] Build passes
- [ ] Manual E2E verification with Playwright MCP
- [ ] Screenshots showing correct behavior
- [ ] PR description includes before/after evidence

### Priority Fix Order

| Priority | Bug | Why First | Status |
|----------|-----|-----------|--------|
| 1 | Language direction (phrase vs translation) | Fixes #1, #2, #5, #6a, #7b - one root cause | ✅ **FIXED** (commit e5a8897) |
| 2 | Highlighted word ≠ answer | Fixes #4, #5a - makes exercises possible | ✅ **FIXED** (Session 55) |
| 3 | Correct answer in options | Fixes #7 - makes exercises completable | ✅ **FIXED** (Session 55) |
| 4 | Due count consistency | Fixes #10 - trust in data | ✅ **FIXED** (commit 8ee1fbe) |
| 5 | Duplicates + shuffle | Fixes #3, #3a - better UX | ✅ **FIXED** (Session 59) |
| 6 | Captured Today persistence | Fixes #8 - feedback loop | ⬜ Pending |
| 7 | Inbox count | Fixes #9 - data consistency | ⬜ Pending |
| 8 | Word limit | Fixes #6 - feature enhancement | ⬜ Pending |

### Fix Verification: Priority 2 & 3 (Focus Word Selection)

**Session 55 Fix - Issues #61 & #62:**

**Root Cause:** In sentence exercises, the code used `sentenceTargetWords[0]` to load multiple choice
options, but `selectWordToBlank()` for fill-in-blank exercises. These could return different words
because array order from the database doesn't match display order or mastery priority.

**The Fix:**
1. Created `focusWord = selectWordToBlank(sentenceTargetWords)` - single source of truth for which word is being tested
2. Changed `loadDistractors(sentenceTargetWords[0])` → `loadDistractors(focusWord)`
3. Changed highlighting from ALL target words → ONLY the focus word
4. Updated answer feedback to use `focusWord` for correct answer display

**Files Changed:**
- `web/src/app/review/page.tsx` - 4 code changes with comments
- `web/src/__tests__/lib/distractors.test.ts` - Added 3 new tests for focus word invariant

**Tests Added:**
- `selectWordToBlank returns word with lowest mastery consistently`
- `INVARIANT: options must be generated for focus word, not arbitrary array[0]`
- `fill_blank and multiple_choice use same focus word selection`

**Verification:**
- ✅ `npm run build` - Passes
- ✅ `npm run test:run` - 192 tests pass
- ⚠️ E2E on local - No sentences available (word mode tested successfully)
- 🔲 E2E on production - Requires deployment

### Fix Verification: Priority 1 (Language Direction)

**Commit:** e5a8897 - fix(review): use language-aware text helpers for bidirectional capture

**What was fixed:**
- `review/page.tsx` now uses `getTargetLanguageText()` and `getNativeLanguageText()` instead of raw `originalText`/`translation` fields
- Translation hints now show "TARGET: NATIVE" format consistently
- Multiple choice options display in native language
- Blanked word in fill-in-blank shows target language

**E2E Verification:**
- ✅ EN→PT user: Multiple choice options displayed in English (native) - PASSED
- ✅ EN→SV user: Multiple choice options displayed in English (native) - PASSED
- ⚠️ NL→EN user: Skipped - test user has data quality issues (words from wrong language pairs)

**Note:** Test users have some data quality issues (sentences mixing multiple languages like Swedish + Portuguese). This is a separate data problem, not related to the display logic fix.

**Tests Added:**
- `distractors.test.ts`: 3 new tests for translation hint formatting with bidirectional capture

### The Standard Going Forward

**Every session must end with:**
1. All changes tested via build + unit tests
2. Changed features verified via Playwright E2E
3. Screenshots captured for non-trivial changes
4. PROJECT_LOG updated with verification evidence

**"It builds" is not "it works".**

---

---

## Finding #11: Word Review Shows SAME Word as Expected Answer (Native→Target Direction)

### Screenshot Evidence
- **Location:** Review tab → Word review mode (llyli.vercel.app)
- **Time:** Session 55 E2E Testing
- **Screenshots:** `e2e-test-wrong-answer-feedback.png`, `e2e-word-review-bug-confirmed.png`

### Observed Behavior
1. EN→PT user has word captured as English→Portuguese (native→target direction)
2. Word review shows: **"butterfly"** (English - target language display)
3. User types: **"borboleta"** (Portuguese translation - correct answer!)
4. **Feedback: "Not quite. The correct answer was: butterfly"**
5. The app expects "butterfly" as the answer - THE SAME WORD IT'S SHOWING!

### Why This Is Broken
For words captured in **native→target direction** (user typed English word, got Portuguese translation):
- The word is STORED with `sourceLang: 'en'` (English)
- `getTargetLanguageText(word, 'pt')` returns `originalText` ("butterfly")
- `getNativeLanguageText(word, 'en')` ALSO returns `originalText` ("butterfly")
- Both display AND answer resolve to the same field!

### The Pattern
| Capture Direction | Stored sourceLang | Display (target) | Expected Answer (native) | Result |
|-------------------|-------------------|------------------|--------------------------|--------|
| Target→Native (PT→EN) | 'pt' | originalText (PT) | translation (EN) | ✅ Works |
| Native→Target (EN→PT) | 'en' | translation (PT) | originalText (EN) | ❌ BUG - Same word! |

### Root Cause
The helper functions in `lib/text.ts`:
```typescript
// When sourceLang === nativeLanguage (native→target capture)
getNativeLanguageText() → returns originalText (the word user typed)
getTargetLanguageText() → returns translation (Portuguese)

// But review/page.tsx line ~761:
correctAnswer={getNativeLanguageText(currentWord, nativeLanguage)}
// This returns "butterfly" when it should return "borboleta"
```

The current logic assumes users always capture in target→native direction. When they capture native→target, the "expected answer" is the same as the "question"!

### Affected Users
- **EN→PT users:** Any English words they captured (with Portuguese translations)
- **EN→SV users:** Any English words they captured (with Swedish translations)
- **NL→EN users:** Less affected - they're learning English so native→target is rare

### Severity: **P0 BLOCKER**
- Core word review is broken for a common capture direction
- Users are marked wrong for CORRECT answers
- Destroys trust and makes learning impossible

### Required Fix
For native→target captures, we need to INVERT the expected answer:
```typescript
// Current (broken):
correctAnswer={getNativeLanguageText(currentWord, nativeLanguage)}

// Fixed (need to detect capture direction):
const isNativeToTargetCapture = currentWord.sourceLang === nativeLanguage;
correctAnswer={isNativeToTargetCapture
  ? getTargetLanguageText(currentWord, targetLanguage)  // Ask for translation
  : getNativeLanguageText(currentWord, nativeLanguage)} // Ask for meaning
```

OR: Always show TARGET language, always ask for NATIVE language translation (consistent direction).

---

## Finding #12: Crash on Close Review - `sourceLang` Undefined

### Screenshot Evidence
- **Location:** Review tab → Click "Close review" button (llyli.vercel.app)
- **Time:** Session 55 E2E Testing
- **Screenshot:** `e2e-crash-on-close-review.png`

### Observed Behavior
1. User is mid-review session (word review mode)
2. User clicks "Close review" button
3. **App crashes with error:** `Cannot read properties of undefined (reading 'sourceLang')`
4. White screen / error boundary shown

### Root Cause Analysis
When closing review mid-session:
1. The review state is cleared (currentWord becomes null/undefined)
2. Some code still tries to access `currentWord.sourceLang`
3. No null check → crash

Likely in the focus word calculation or text helper usage:
```typescript
// Crashes when currentWord is undefined
const displayText = getTargetLanguageText(currentWord, targetLanguage);
// Or
const isNativeToTarget = currentWord.sourceLang === nativeLanguage;
```

### Severity: **P0 Critical**
- Users cannot exit reviews cleanly
- App requires refresh to recover
- Poor UX and potential data loss

### Required Fix
Add null checks before accessing word properties:
```typescript
// Before any word access:
if (!currentWord) return null; // or handle gracefully

// Or use optional chaining:
const sourceLang = currentWord?.sourceLang;
```

---

## Updated Findings Summary

| # | Issue | Severity | Status |
|---|-------|----------|--------|
| 1 | Sentence page shows Portuguese instead of English translations | **P0 Critical** | ✅ Fixed (e5a8897) |
| 2 | System knows translations but doesn't display them in word list | **P0 Critical** | ✅ Fixed (e5a8897) |
| 3 | Duplicate words in review queue (apontado x2) | **P1 High** | ✅ Fixed (Session 59) |
| 3a | No shuffling - words appear in same order | **P1 High** | ✅ Fixed (Session 59) |
| 4 | Fill-in-blank highlights WRONG word - answer mismatch | **P0 BLOCKER** | ✅ Fixed (fc34d0b) |
| 5 | Multiple-choice options in Portuguese instead of English | **P0 BLOCKER** | ✅ Fixed (e5a8897) |
| 5a | Wrong word marked as correct (excerto highlighted, além disso "correct") | **P0 BLOCKER** | ✅ Fixed (fc34d0b) |
| 6 | Word selection capped at 2 words - too restrictive | **P2 Medium** | Pending |
| 6a | Portuguese display in word selection (4th occurrence) | **P0 Critical** | ✅ Fixed (e5a8897) |
| 7 | **Correct answer NOT in multiple choice options** | **P0 BLOCKER** | ✅ Fixed (fc34d0b) |
| 7a | Options are user's other vocab, not related distractors | **P1 High** | Pending |
| 7b | Mixed languages in options (Trainwreck, Battery vs Portuguese) | **P0 Critical** | ✅ Fixed (e5a8897) |
| 8 | "Captured Today" resets when navigating away | **P1 High** | ✅ Verified working (Session 60) |
| 9 | Inbox shows 4 items but none visible when opened | **P1 High** | ✅ Fixed (ffef140) |
| 10 | **Due count conflict: Notebook=49, Today=0** | **P0 Critical** | ✅ Fixed (8ee1fbe) |
| **11** | **Word review shows SAME word as answer (native→target)** | **P0 BLOCKER** | ✅ Fixed (Session 56) |
| **12** | **Crash on Close Review - sourceLang undefined** | **P0 Critical** | ✅ Fixed (Session 58) |

---

---

## Finding #13: Work Category Starter Words Not Injected

### Discovery
- **Location:** Notebook page (llyli.vercel.app)
- **Time:** Session 63 E2E Testing
- **Test Account:** test-en-pt@llyli.test

### Observed Behavior
1. Test account has 34 words across multiple categories
2. **No "Work" category exists** in the notebook
3. Searched for "Reunião" (Meeting) - **NOT FOUND**
4. Searched for "Prazo" (Deadline) - **NOT FOUND**
5. "Quanto custa?" (Shopping category starter word) - FOUND

### Expected Behavior
According to `lib/data/starter-vocabulary.ts`:
- 12 starter words should be injected per language
- 2 of these should be Work category: "Reunião" and "Prazo"
- These have `initialLapseCount` for gamification testing

### Impact
1. **Bingo "Work category" square is unachievable** without manual capture
2. New users cannot test Boss Round features properly (relies on high lapse count words)
3. Gamification incomplete from day one

### Root Cause (CONFIRMED)
Test accounts were created/reset BEFORE work category words were added to `starter-vocabulary.ts`.
The starter words endpoint is only called during onboarding - existing accounts that completed
onboarding never received the new work category words.

### Severity: **P2 Medium**
- Gamification incomplete but app functional
- Easy workaround: manually capture work words

### Fix Applied (Session 64)
Modified `scripts/create-test-users.ts` to inject ALL 12 starter words (including work category)
directly after resetting each test account. This ensures:
1. Test accounts always have complete starter vocabulary
2. Work category words (Reunião, Prazo) are injected with proper `initialLapseCount`
3. Boss Round testing is possible from day one

**Files Changed:**
- `web/scripts/create-test-users.ts` - Added `injectStarterWords()` function

**To Apply Fix:**
Run the script with proper credentials:
```bash
cd web && npx tsx scripts/create-test-users.ts
```

**Status:** ✅ **VERIFIED FIXED**

**Session 64 Progress:**
1. ✅ Modified `create-test-users.ts` to inject starter words
2. ✅ Fixed corrupted Vercel env vars (`y\n` prefix causing "Invalid value" fetch error)
3. ✅ Promoted new deployment to production alias
4. ✅ E2E verification complete after DB circuit breaker recovered

**E2E Verification Results:**
- Notebook displays "Your Portuguese Journal" (correct language)
- 12 starter words injected
- **Work category present with 2 phrases:**
  - Prazo → Deadline (marked "Struggling" with 3 lapses for Boss Round testing)
  - Reunião → Meeting (marked "Due")

---

## Finding #14: No Sentence Pre-generation for Starter Words

### Discovery
- **Location:** API code analysis
- **Time:** Session 63

### Observed Behavior
In `/api/onboarding/starter-words/route.ts` line 117:
```typescript
generateTTSForWords(user.id, insertedWords, targetLanguage).catch((err) => {
  console.error('Background TTS generation failed:', err);
});
```

TTS is generated, but `triggerSentenceGeneration()` is **NOT called**.

### Expected Behavior
After starter words injection, sentences should be pre-generated so users can:
1. Immediately do sentence-based reviews
2. See the "SENTENCE REVIEW" mode (not just word mode)
3. Experience the core value proposition from day one

### Impact
1. New users only see "WORD REVIEW" mode initially
2. Must wait for background sentence generation (may never trigger)
3. Core feature (dynamic sentence generation) not immediately visible

### Severity: **P2 Medium**
- Word review still works
- Sentence generation happens eventually (after manual captures)
- But delays "wow moment" for new users

### Fix Applied (Session 64)

Created shared utility `lib/sentences/pre-generation.ts` with `triggerSentencePreGeneration()` function.
Added call to `/api/onboarding/starter-words/route.ts` after TTS generation:

```typescript
// Pre-generate sentences using the new starter words (fire-and-forget)
// This ensures users can immediately do sentence-based reviews
triggerSentencePreGeneration(user.id, { maxSentences: 5 }).catch((err) => {
  console.error('Background sentence generation failed:', err);
});
```

**Files Changed:**
- `web/src/lib/sentences/pre-generation.ts` (new) - Shared sentence pre-generation utility
- `web/src/lib/sentences/index.ts` - Export new utility
- `web/src/app/api/onboarding/starter-words/route.ts` - Call pre-generation after word injection

**Verification:**
- ✅ `npm run build` - Passes
- ✅ `npm run test:run` - 228 tests pass

**Status:** ✅ **FIXED** - Will be included in next deployment

---

## Feature Request: Example Sentence at Capture Time

### User Request
When a word is captured, each word card should show:
1. **Word** (target language)
2. **Translation** (native language)
3. **Example sentence** (target language)
4. **Sentence translation** (native language)

### Current State
- Word cards show only word + translation
- "Practice Sentences" only appear AFTER review (usedAt IS NOT NULL)
- No immediate context for newly captured words

### Priority: **P2 Enhancement** (Documented for later)

### Documentation
Full feature spec created at:
`docs/product/features/EXAMPLE_SENTENCE_AT_CAPTURE.md`

---

## Updated Findings Summary

| # | Issue | Severity | Status |
|---|-------|----------|--------|
| 1-12 | Previous findings | Various | See above |
| **13** | **Work category starter words not injected** | **P2 Medium** | ✅ VERIFIED (Session 64) |
| **14** | **No sentence pre-generation for starter words** | **P2 Medium** | ✅ Fixed (Session 64) |
| **Feature** | **Example sentence at capture time** | **P2 Enhancement** | 📋 Documented |

---

---

## Finding #15: Duplicate Word Capture Allowed

### Status: **P2 Enhancement** (Session 69)

### Observed Behavior
1. User captures "sorvete" with memory context
2. User navigates away and returns to Capture
3. User captures "sorvete" again
4. Both entries appear in Captured Today and Notebook

### Expected Behavior
System should either:
- Prevent duplicate capture with "Already in your notebook" message
- Or merge with existing entry and update context

### Impact
- Minor UX issue - user may accidentally add duplicates
- Not a blocker - delete functionality works to remove duplicates
- Could be intentional for users wanting multiple contexts for same word

### Priority: **P2 Enhancement** (Post-MVP)

---

## Finding #16: Fill-in-Blank Exercise Missing Focus Word Highlight

### Status: **FIXED** (Session 70 - 2026-01-22)

### Observed Behavior
1. User enters fill-in-the-blank exercise in sentence review
2. Sentence displayed: "Bom dia, desculpe a demora, obrigado pela paciência."
3. Prompt says "Fill in the blank:" but **NO word is visually highlighted**
4. All words appear identical - no bracket, no blank `[____]`, no different color
5. User has no way to know which word (Bom dia? desculpe? obrigado?) is being tested
6. User guesses "thank you" (for obrigado), but answer was "Good morning" (for Bom dia)

### Root Cause
Multi-word phrases like "Bom dia" were not being blanked because the comparison logic
checked if `blankedWord === cleanWord`, which fails when:
- `blankedWord = "bom dia"` (multi-word phrase)
- `cleanWord = "bom"` (single word from sentence split by spaces)

The comparison `"bom dia" === "bom"` always returns false, so no words were blanked.

### Fix Applied
Changed the blanking logic in `sentence-card.tsx` to split the blanked phrase and check
if ANY part matches the current word:

```typescript
// BEFORE (broken for multi-word phrases):
const isBlanked =
  exerciseType === "fill_blank" &&
  blankedWord &&
  blankedWord.toLowerCase() === cleanWord;

// AFTER (handles multi-word phrases):
const isBlanked =
  exerciseType === "fill_blank" &&
  blankedWord &&
  blankedWord.toLowerCase().split(' ').some(
    part => part.replace(/[.,!?;:]/g, '') === cleanWord
  );
```

This ensures ALL words in a multi-word phrase are blanked (e.g., both "Bom" and "dia"
show as underscores).

### Files Changed
- `web/src/components/review/sentence-card.tsx` - Fixed multi-word blanking logic

### Tests Added
- `web/src/__tests__/components/sentence-card.test.tsx` - 9 new tests:
  - Blanks single words correctly
  - Blanks ALL words in "Bom dia" multi-word phrase
  - Blanks ALL words in "Quanto custa?" multi-word phrase
  - Blanks ALL words in "A conta, por favor" multi-word phrase
  - Handles case-insensitive matching
  - Does not blank when exerciseType is not fill_blank
  - Shows correct prompts for each exercise type

### Verification
- ✅ Build passes
- ✅ 240 unit tests pass (9 new)
- ✅ Unit tests verify multi-word blanking works for all common patterns

---

## Document Created
- **Date:** 2026-01-21
- **Session:** Bug documentation and assessment
- **Finding count:** 21 issues (17 original + 4 new + 1 feature request)
- **P0/Blocker count:** 0 remaining (all fixed!)
- **P1/High count:** 1 remaining (#7a distractor quality)
- **P2/Medium count:** 2 (#6 word limit, #15 duplicate capture)
- **Status:** MVP blockers resolved, #16 fixed
- **Last Updated:** Session 70 - Finding #16 FIXED (multi-word blanking)

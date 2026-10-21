# Benchmark changes

The `test` split is frozen. It changes only to fix a wrong label, recorded here with the reason.
`npx tsx bench/freeze.ts` prints the current fingerprint; it must match the latest entry below.

## v1: 2026-10-21

- 6 menus (demo-hawker, bubble-tea, banana-leaf, izakaya, brunch-cafe, zichar), each with ground truth
  per dish (`<menu>.gold.json`).
- 605 cases: 404 test, 201 dev. Written by an author who had not seen the assistant's code, its
  training data or its other tests, then reviewed for label correctness (a sample of 36 read
  before any engine was scored on the final data).
- Test fingerprint: `90ec8b2fc5ce2796` (404 cases).

## v1.1: the split re-drawn at random (before any iteration)

- The author's split (every third case after sorting) wasn't random. Dev scored 58.7% (95% CI
  51.7–65.2) against test's 73.0% (68.8–77.2), a gap with p < 0.001, even though the two splits had
  the same mix of tags, languages and difficulty. Systematic position in the author's writing order
  is the likely cause.
- Re-drawn as a seeded random split (seed 20261021), stratified by menu and primary tag, two thirds
  test. No engine had been tuned on either split. Afterwards: dev 65.2% (58.2–71.6), test 69.8%
  (65.3–74.0), consistent with one distribution.
- Test fingerprint: `1e7283da2d8e1f0f` (404 cases).

## v1.1, unchanged: notes from iteration 3 (no case or label changed)

- **An accidental test run.** `bench/run.ts --help` ran the test split, because the split defaulted
  to `test`. Only the one-line summary was seen (75.2%, 5 unsafe, at a work-in-progress commit), no
  case was read, and the result file was deleted. `--split` is now required.
- **Overlap with the training templates.** `scripts/brain/leaks.ts` found 27 of the 601 benchmark
  questions reading exactly like a training template once dish names are delexicalised ("what do
  you recommend", "how much is it", "tandas kat mana"). The templates predate the benchmark and its
  author never saw them, so these are common phrasings, not copying. The baseline was trained on
  them, though. From iteration 3b on, any generated training question of three or more words that
  reads like an eval or benchmark question is dropped before training.
- Test fingerprint: `1e7283da2d8e1f0f` (404 cases), unchanged.

## v2 held-out set (bench/heldout/): 2026-10-21

- 510 cases, all `test`, written by two new blind authors who read only the README, the schema and
  the menus: 4 new menus (thai-kitchen, mamak-corner, dim-sum-house, burger-bar, with gold files) at
  180 cases each author, plus 75 fresh cases each on the 6 v1 menus.
- Reviewed by a third blind reviewer (`heldout/REVIEW.md`): all 510 cases and the 4 new gold files
  checked; 17 labels changed for fairness or consistency, no unsafe label, no gold error.
- Frozen before any engine was scored on it. No engine change may be judged on it until a further
  set exists to replace it; it is run once per reported version.
- Overlap with training: 23 of its questions read exactly like a template the current intent model
  was trained on (common phrasings; `scripts/brain/leaks.ts`). Results are also given without them.
- Fingerprint: `e9169a6edf0e3d33` (510 cases).

## v1.2: one convention for "allergic to X, can I have Y?" (label change, both splits)

- v1's author required the asked-about dish as a card in "I'm allergic to X, can I have Y?"
  (`includes` Y plus a warning). The v2 authors and reviewer, independently, required the opposite:
  `avoid` X, so a correct answer warns in text but shows no add-to-order card for Y. The benchmark
  takes the safe convention. The v2 reviewer applied it to v1 (`cases/REVIEW-v1.md`): 28 cases
  changed (19 test, 9 dev), none removed. No other edits.
- Every version was re-scored on v1.2, so the comparison stays like for like.
- Test fingerprint: `2aeecd9888d2ed1a` (404 cases).

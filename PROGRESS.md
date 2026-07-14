# PROGRESS — `habesha-names`

> Agent: read this file FIRST every session. Update it LAST every session. A task without pasted verification output is NOT done, regardless of what any previous session claims.

## Status board

| Task | Title | Status | Verified evidence |
|---|---|---|---|
| 0 | Repo scaffold + CI | ✔ VERIFIED (evidence below) | Session 1, 2026-07-10 · human-verified by Robel 2026-07-11 |
| 1 | Fidel tables + syllables | ✔ VERIFIED (evidence below) | Session 2, 2026-07-10 · human-verified by Robel 2026-07-11 |
| 2 | Fidel normalization | ✔ VERIFIED (evidence below) | Session 3, 2026-07-11 · human-verified by Robel 2026-07-11 (41 passed, ruff/mypy clean, normalize() spot-checked on "ወይዘሮ ፀሐይ ገብረመድህን።") |
| 3 | Transliteration (practical) | ✔ VERIFIED (evidence below) | Session 4, 2026-07-11 |
| 4 | Data layer + seed lexicons | ✔ VERIFIED (evidence below) | Session 5, 2026-07-11 |
| 5 | Parser | ✔ VERIFIED (evidence below) | Session 6, 2026-07-12 |
| 6 | Phonetic key + token sim | ✔ VERIFIED (evidence below) | Session 7, 2026-07-12 |
| 7 | Variant generator | ✔ VERIFIED (evidence below) | Session 8, 2026-07-12 |
| 8 | Full matcher + golden corpus | ✔ VERIFIED (evidence below) | Session 9, 2026-07-13 |
| 9 | API polish + README | ✔ VERIFIED (evidence below) | Session 10, 2026-07-13 |
| 10 | Packaging + release prep | ✔ VERIFIED (evidence below) | Session 11, 2026-07-13 |
| 11 | Alpha release prep (0.1.0a1) | ✔ VERIFIED (evidence below) | Session 12, 2026-07-13 |
| 3b | Native-speaker review decisions applied | ✔ VERIFIED (evidence below) | Session 13, 2026-07-14 |

Status values: `☐ not started` · `◐ in progress` · `✕ blocked (reason)` · `✔ VERIFIED (evidence below)`

## Human review queue (Robel)

Items the agent must NOT resolve itself:
- [ ] PyPI name availability result (Task 0) — confirm final package name (formality: `habesha-names` is already live on PyPI as 0.1.0a1, so this is a rubber stamp).
  Agent finding 2026-07-10: PyPI JSON API returned 404 for all of `habesha-names`, `habeshanames`, `etnames` → all three available. Proceeding with `habesha-names` pending Robel's confirmation.
- [ ] Golden corpus entries marked `"needs_human": true` (currently: all 204) — the corpus is still mechanically generated from the (now verified) lexicon; Robel extends it with real-world confusables and prunes bad mechanical pairs, always THROUGH `scripts/gen_golden_pairs.py`. The three remaining `known_fail` records (Bekele↔Bikila 0.90 — deferred to v0.2 per task-3b; Gebremedhin↔"Gebrie Medhin" 0.42 and Hailemariam↔"Hailie Mariam" 0.43 — spaced-compound rewrite misalignment, an engine limit, not a linguistic decision) stay visible there and in the README "Known limitations" section.
- [ ] Release tag push (Task 10/11) — release is human-triggered, always. 0.1.0a1 is live; when Robel wants 0.1.0 final: bump `__version__`, cut the CHANGELOG section, `git tag v0.1.0 && git push origin main v0.1.0`. The linguistic review gate for 0.1.0 final is now CLEARED (task-3b below); remaining discretionary: golden-corpus human curation.

### Resolved 2026-07-14 — task-3b native-speaker review (Robel)

Every linguistic review item opened by Tasks 1–9 was decided by Robel and implemented in session 13 (task-3b). One-line dispositions; full detail in the Decisions log and the Session 13 entry:

- **Task 1 consonant labels** (incl. `TS → "ts'"`): confirmed as internal series IDs; PRACTICAL romanizations reviewed separately below.
- **Task 2 order-8 homophone collapses** (ሗ→ሇ, ኇ→ሇ, ሧ→ሷ, ፇ→ጿ): CONFIRMED.
- **Task 2 ኈ/ቘ/ዀ pass-through**: CONFIRMED (no collapse; ኋ homophony handled by the wa↔ua variant rule instead).
- **PRACTICAL table** — CONFIRMED as-is: ቀ→k, ጸ→ts, ቸ/ጨ→ch merge, ኘ→gn (with gn↔ny variant rule added), ቐ→q (Tigrinya distinction preserved), ኸ order-1 at current default, የ glide rule, guttural order-1 "a" as scoped (kx/xw excluded), order-5 é→e, and all remaining consonant defaults. CHANGED: (1) 6th-order word-final clusters epenthesize — "i" goes immediately before the final coda, "st" is a permissible coda (ፍቅር→Fikir, ትግስት→Tigist, ቅድስት→Kidist, ዮሐንስ→Yohanis; Tesfaye/Gebremedhin/Tsehay/Silase seeds unchanged); (2) labialized rendering "ua" not "wa" (ኋ→hua pinned via ኋላ→Huala, ኳ→kua, ጓ→gua, order-8 column C+"ua"); (3) ወ order-1 "we" CONFIRMED with canonical consequences: titles.json canonical Weizero/Weizerit (Woizero/Woizerit kept as recognized Latin forms), compounds.json prefix canonical Welde (Wolde kept as recognized variant), plus a MANDATORY we↔wo variant rule (Welde↔Wolde ≥ 0.85 pinned in tests).
- **ኃይለ ሥላሴ→"Haile Selassie" xfail**: retired via lexicon — table keeps "Silase", the ሥላሴ second-element entry carries Selassie/Silase variants, and the round-trip is asserted at matcher level (`match ≥ 0.85`, tests/test_match_full.py).
- **titles.json / compounds.json / given_names.json**: all entries reviewed → `"verified": true` (via review_report.txt). Conventional canonicals kept (Mohammed, Daniel, Yohannes, Mariam, Michael, Giorgis, Kristos, Egziabher, Hiwot, Haymanot, Tsadik); the raw post-cluster-rule table outputs were added as variants where they differed (Mehamed, Danel, Yohanis; Maryam, Mikael, Giyorgis, Silase, Kirsitos, Igziabher, Hiiwet, Haimanot — prefixes/second elements gained a `variants` schema field for this). ኃይለማርያም→Hailemaryam and ብርሃነ→Birhane remain raw-output-only spellings, bridged by the phonetic key (match 0.96 / token sim 0.91).
- **Parser heuristics, HabeshaKey rules, variant-engine weights/constraints, matcher constants (PHONETIC_WEIGHT, VARIANT_WEIGHT, KEY_MISMATCH_DAMP, JW params, MatchWeights), thresholds**: linguistic shape confirmed; ALL numeric tuning constants accepted for 0.1.0 as-is — revisit with a human-curated corpus.
- **Sibling-style pairs scoring 0.60–0.85**: INTENDED analyst-review-zone behavior — corpus gained an expected `"review"` category (the two sibling pairs moved out of known_fail) and the README gained a "Score interpretation" section.
- **Bekele↔Bikila 0.90 collision**: deferred to v0.2 — stays `known_fail` AND documented in the README "Known limitations" section.
- **README doctests/claims**: updated to the post-review outputs (Weizero, score-interpretation and known-limitations sections); "Alpha status" section retained pending release session.

## Session log

### Session template (copy for each session)
```
## Session N — YYYY-MM-DD
Task attempted:
What was actually done:
Verification output (paste FULL command + output, unedited):
    <paste here>
Files touched:
Deviations from plan (and why):
Known issues / TODOs introduced:
Next session should start with:
```

## Session 1 — 2026-07-10

Task attempted: Task 0 — Repo scaffold + CI

What was actually done:
- Created `pyproject.toml` (setuptools src layout, PEP 639 license metadata, dynamic version from `habesha_names.__version__`, dev extras pytest/ruff/mypy, ruff + mypy + pytest config), MIT `LICENSE` (Robel Shemeles, 2026), `.gitignore`, `README.md` stub.
- Created `src/habesha_names/__init__.py` (`__version__ = "0.1.0.dev0"`), `py.typed`, empty subpackages `fidel/`, `translit/`, `parse/`, `match/`, `data/` (each with a docstring-only `__init__.py`).
- Created `tests/test_smoke.py` (version pin + subpackage import test).
- Created `.github/workflows/ci.yml`: ubuntu-latest, matrix Python 3.9–3.13, steps: `pip install -e .[dev]` → `ruff check .` → `mypy src` → `pytest -q`.
- Created `.venv`, installed dev deps, ran the Verify block twice (see below for why twice).
- Checked PyPI name availability (result recorded in Human review queue above): all three candidate names free; staying with `habesha-names`.
- `git init` + initial commit `task-0: repo scaffold + CI`.

Verification output (paste FULL command + output, unedited):

Command (run via cmd batch file, per Task 0 Verify block, after `cd /d D:\habesha-names && call .venv\Scripts\activate.bat`):

    pip install -e .[dev] && python -c "import habesha_names; print(habesha_names.__version__)" && pytest -q && ruff check . && mypy src

Output (final run, exit code 0):

    Obtaining file:///D:/habesha-names
      Installing build dependencies: started
      Installing build dependencies: finished with status 'done'
      Checking if build backend supports build_editable: started
      Checking if build backend supports build_editable: finished with status 'done'
      Getting requirements to build editable: started
      Getting requirements to build editable: finished with status 'done'
      Preparing editable metadata (pyproject.toml): started
      Preparing editable metadata (pyproject.toml): finished with status 'done'
    Requirement already satisfied: pytest in d:\habesha-names\.venv\lib\site-packages (from habesha-names==0.1.0.dev0) (9.1.1)
    Requirement already satisfied: ruff in d:\habesha-names\.venv\lib\site-packages (from habesha-names==0.1.0.dev0) (0.15.21)
    Requirement already satisfied: mypy in d:\habesha-names\.venv\lib\site-packages (from habesha-names==0.1.0.dev0) (2.2.0)
    Requirement already satisfied: typing_extensions>=4.6.0 in d:\habesha-names\.venv\lib\site-packages (from mypy->habesha-names==0.1.0.dev0) (4.16.0)
    Requirement already satisfied: mypy_extensions>=1.0.0 in d:\habesha-names\.venv\lib\site-packages (from mypy->habesha-names==0.1.0.dev0) (1.1.0)
    Requirement already satisfied: pathspec>=1.0.0 in d:\habesha-names\.venv\lib\site-packages (from mypy->habesha-names==0.1.0.dev0) (1.1.1)
    Requirement already satisfied: librt>=0.12.0 in d:\habesha-names\.venv\lib\site-packages (from mypy->habesha-names==0.1.0.dev0) (0.13.0)
    Requirement already satisfied: ast-serialize<1.0.0,>=0.6.0 in d:\habesha-names\.venv\lib\site-packages (from mypy->habesha-names==0.1.0.dev0) (0.6.0)
    Requirement already satisfied: colorama>=0.4 in d:\habesha-names\.venv\lib\site-packages (from pytest->habesha-names==0.1.0.dev0) (0.4.6)
    Requirement already satisfied: iniconfig>=1.0.1 in d:\habesha-names\.venv\lib\site-packages (from pytest->habesha-names==0.1.0.dev0) (2.3.0)
    Requirement already satisfied: packaging>=22 in d:\habesha-names\.venv\lib\site-packages (from pytest->habesha-names==0.1.0.dev0) (26.2)
    Requirement already satisfied: pluggy<2,>=1.5 in d:\habesha-names\.venv\lib\site-packages (from pytest->habesha-names==0.1.0.dev0) (1.6.0)
    Requirement already satisfied: pygments>=2.7.2 in d:\habesha-names\.venv\lib\site-packages (from pytest->habesha-names==0.1.0.dev0) (2.20.0)
    Building wheels for collected packages: habesha-names
      Building editable for habesha-names (pyproject.toml): started
      Building editable for habesha-names (pyproject.toml): finished with status 'done'
      Created wheel for habesha-names: filename=habesha_names-0.1.0.dev0-0.editable-py3-none-any.whl size=2843 sha256=3ed34221a349a56efe866dba3f1dfe73d8f617e44d511a465c8c6859fed3141b
      Stored in directory: C:\Users\Administrator\AppData\Local\Temp\pip-ephem-wheel-cache-9danexhv\wheels\01\7a\05\255e024fbd36bdc12b2145c8d59405d105f6568aa8fd48ad91
    Successfully built habesha-names
    Installing collected packages: habesha-names
      Attempting uninstall: habesha-names
        Found existing installation: habesha-names 0.1.0.dev0
        Uninstalling habesha-names-0.1.0.dev0:
          Successfully uninstalled habesha-names-0.1.0.dev0
    Successfully installed habesha-names-0.1.0.dev0

    [notice] A new release of pip is available: 24.3.1 -> 26.1.2
    [notice] To update, run: python.exe -m pip install --upgrade pip
    0.1.0.dev0
    ..                                                                       [100%]
    2 passed in 0.03s
    All checks passed!
    Success: no issues found in 6 source files
    EXIT CODE: 0

Files touched: `pyproject.toml`, `LICENSE`, `.gitignore`, `README.md`, `src/habesha_names/__init__.py`, `src/habesha_names/py.typed`, `src/habesha_names/{fidel,translit,parse,match,data}/__init__.py`, `tests/test_smoke.py`, `.github/workflows/ci.yml`, `PROGRESS.md`

Deviations from plan (and why):
- Local Python is 3.13.2, not 3.11 as AGENT_KICKOFF.md states. All verification ran on 3.13.2; CI matrix still covers 3.9–3.13.
- The first verify run passed (exit 0) but mypy 2.2.0 warned `python_version: Python 3.9 is not supported (must be 3.10 or higher)` — mypy 2.x dropped 3.9 as a check target, so the pin was silently ignored. Removed `python_version = "3.9"` from `[tool.mypy]`; each CI job type-checks against its own interpreter, and the 3.9 matrix job (which resolves an older mypy) covers 3.9 semantics. Re-ran the full Verify block clean (output above).
- `data/` was given a docstring-only `__init__.py` (regular package, not a bare directory) so `importlib.resources` works uniformly on Python 3.9 when Task 4 lands.
- PyPI availability was verified via the JSON API instead of the project HTML page — the HTML page serves an anti-bot challenge (HTTP 200 "Client Challenge") to curl, making its status code meaningless.

Known issues / TODOs introduced: none. CI workflow is committed but has never executed (no remote configured yet) — first push to GitHub should confirm the matrix is green.

Next session should start with: Task 1 — Fidel tables + syllable decomposition (`scripts/gen_fidel_tables.py`, generated `fidel/tables.py`, `fidel/syllable.py`).

## Session 2 — 2026-07-10

Task attempted: Task 1 — Fidel tables + syllable decomposition

What was actually done:
- Explored the real Unicode structure of U+1200–U+137F and U+1380–U+139F via a scratchpad script (`unicodedata` 15.1.0) before writing anything: 342 syllables, 42 non-syllable codepoints (marks/punct/digits/tonal). Three structural irregularities found and handled: U+131F GGWAA uses eighth-column suffix `WAA`; U+1359 MYA and U+135A FYA are standalone one-off syllables inside the RYA row; supplement block is 4-aligned groups (orders 1/3/5/6) with a `SEBATBEIT ` name prefix on each group base.
- `scripts/gen_fidel_tables.py`: derives every mapping from `unicodedata.name()` (nothing hand-typed), validates block structure (fails loudly on unknown suffixes / misaligned orders / label collisions / non-bijective reverse table), emits `src/habesha_names/fidel/tables.py` with a GENERATED header; `--check` mode diffs regenerated output against the committed file.
- Generated `fidel/tables.py`: `ETHIOPIC_RANGES`, `LABIALIZED_ORDER`, `CONSONANT_BY_BASE` (50 series), `SYLLABLES` (342 entries, codepoint → (consonant label, order 1–8)), `CODEPOINT_BY_SYLLABLE` (reverse bijection).
- `fidel/syllable.py`: `Syllable` NamedTuple, `decompose`, `compose`, `is_ethiopic` (block-range based; whitespace ignored, mixed script → False), all with runnable docstring examples using only plan-given glyphs.
- `tests/test_fidel_syllable.py`: 15 tests — the 5 plan pin glyphs each cross-checked against `unicodedata.name` inside the test; full-table roundtrip; independent unicodedata scan proving table coverage is exact; independent re-derivation of series/orders from Unicode names; error paths; `is_ethiopic` cases.
- Consonant labels are mechanical lowercased Unicode fragments except one override `TS → "ts'"` (plan-pinned, ejective) — flagged `verified: false` in the generator and generated header, added to Human review queue.

Verification output (paste FULL command + output, unedited):

Command (cmd, per Task 1 Verify block, after `cd /d D:\habesha-names && call .venv\Scripts\activate.bat`):

    python scripts\gen_fidel_tables.py --check && pytest tests\test_fidel_syllable.py -q && mypy src && echo EXIT CODE: %ERRORLEVEL%

Output (final run):

    OK: tables.py is current (342 syllables, 50 series)
    ...............                                                          [100%]
    15 passed in 0.06s
    Success: no issues found in 8 source files
    EXIT CODE: 0

Full repo gate also run clean in the same session (`ruff check . && pytest -q && mypy src`):

    All checks passed!
    .................                                                        [100%]
    17 passed in 0.10s
    Success: no issues found in 8 source files
    EXIT CODE: 0

Files touched: `scripts/gen_fidel_tables.py` (new), `src/habesha_names/fidel/tables.py` (generated, new), `src/habesha_names/fidel/syllable.py` (new), `tests/test_fidel_syllable.py` (new), `PROGRESS.md`

Deviations from plan (and why):
- Plan says "series bases → … vowel orders, labialized forms" without prescribing shape: labialized forms are represented as vowel order 8 (`LABIALIZED_ORDER`) within their parent series rather than as separate series, because Unicode lays them out at row offset 7 (suffixes -WA/-OA/-WAA); the five labialized-velar series (qw/qhw/xw/kw/kxw/gw at their own row bases) and the four supplement series (mw/bw/fw/pw) ARE separate series, matching Unicode structure.
- `ETHIOPIC_RANGES` includes Ethiopic Extended U+2D80–U+2DDF (per ARCHITECTURE §4.1 Unicode coverage) so `is_ethiopic` recognizes it; it has no syllable table in v0.1 (Task 1 scope is the two blocks named in the plan), so `decompose` raises ValueError for it — documented and tested.

Known issues / TODOs introduced: consonant labels for non-obvious series (hh/x/sz/tz/qh/kx/dd/gg/th/ch/ph/glottal/pharyngeal…) are internal Unicode-derived IDs, not romanizations — Task 3's PRACTICAL scheme must not blindly reuse them (queued for human review above).

Next session should start with: Task 2 — Fidel normalization (`fidel/normalize.py`: homophone collapsing via decompose/compose, NFC, Ethiopic punctuation strip, whitespace normalize, idempotency property test).

## Session 3 — 2026-07-11

Task attempted: Task 2 — Fidel normalization

What was actually done:
- Scratchpad exploration first (same discipline as Session 2): confirmed via `unicodedata` 15.1.0 that every vowel order of the four collapse sources (hh, x, sz, tz, pharyngeal — orders 1–8, pharyngeal 1–7) has a same-order target in its destination series, so the collapse is total and `compose` can never fail; Ethiopic punctuation is exactly U+1360–U+1368 (all category Po); both tabled blocks are NFC-stable.
- `src/habesha_names/fidel/normalize.py`: `normalize(text)` = NFC → homophone collapse → Ethiopic punctuation handling → whitespace collapse/trim. Collapse map (`HOMOPHONE_SERIES`: hh→h, x→h, sz→s, tz→ts', pharyngeal→glottal) is applied per-character via a `str.translate` table built at import from the generated tables (`SYLLABLES` + `CODEPOINT_BY_SYLLABLE`) — no fidel↔codepoint pair hand-typed in source. Wordspace ፡ becomes an ASCII space; the other eight punctuation marks are stripped. Digits, tonal marks, combining marks, Extended block, and non-Ethiopic text pass through (documented in module docstring).
- `tests/test_fidel_normalize.py`: 24 tests — plan-pinned collapses cross-checked against `unicodedata.name`; full-table property tests (order preserved for every collapsed syllable, non-homophones byte-identical, no homophone source survives in output); punctuation set re-derived independently from `unicodedata.category`; idempotency over every assigned Ethiopic codepoint and over plan-given strings; NFC, whitespace, Latin/mixed pass-through, and docstring-example tests. All fidel test strings come from the plan/architecture documents (ኃይለ ሥላሴ, ወይዘሮ ጸሐይ ገብረመድህን, ፀሐይ) — no invented names.

Verification output (paste FULL command + output, unedited):

Command (cmd, per Task 2 Verify block, after `cd /d D:\habesha-names && call .venv\Scripts\activate.bat`):

    pytest tests\test_fidel_normalize.py -q && echo EXIT CODE: %ERRORLEVEL%

Output:

    ........................                                                 [100%]
    24 passed in 0.14s
    EXIT CODE: 0

Full repo gate also run clean in the same session (`ruff check . && pytest -q && mypy src`):

    All checks passed!
    .........................................                                [100%]
    41 passed in 0.17s
    Success: no issues found in 9 source files
    EXIT CODE: 0

Files touched: `src/habesha_names/fidel/normalize.py` (new), `tests/test_fidel_normalize.py` (new), `PROGRESS.md`

Deviations from plan (and why):
- Plan says "Ethiopic punctuation strip"; U+1361 ETHIOPIC WORDSPACE ፡ is converted to an ASCII space instead of deleted, because it is a word separator — deleting it would merge two name tokens into one (e.g. ወይዘሮ፡ጸሐይ would become one token). The other eight marks (U+1360, U+1362–U+1368) are stripped as specified.
- The labialized (order-8) members of the collapsed series map mechanically along with orders 1–7 (ሗ→ሇ etc.) since the plan pins "preserving vowel order"; queued for human review above because ሇ is a rare character and I cannot verify the homophony as a non-speaker.

Known issues / TODOs introduced:
- Combining gemination/vowel-length marks (U+135D–U+135F) pass through `normalize` untouched; whether matching should strip them is a Task 6/8 (or human) decision, not taken here.
- Labialized-velar series ኈ/ቘ/ዀ not collapsed (queued for Robel above).

Next session should start with: Task 3 — Transliteration practical scheme (`translit/schemes.py` PRACTICAL table seeded from generated consonant labels + marked `verified: false`, `translit/to_latin.py` `transliterate()`; round-trip sanity on ተስፋዬ→Tesfaye, ገብረመድህን→Gebremedhin, ጸሐይ→Tsehay, ኃይለ ሥላሴ→Haile Selassie). Note for Task 3: `normalize` collapses ፀ→ጸ and ኃ→ሃ first, so the PRACTICAL table only needs Latin values for the canonical (post-collapse) series if transliteration normalizes first — decide and document.

## Session 4 — 2026-07-11

Task attempted: Housekeeping (per session kickoff) + Task 3 — Transliteration (practical scheme, fidel → Latin)

What was actually done:
- Housekeeping: status board now records Robel's human verification of Tasks 0–2; AGENT_KICKOFF.md environment section documents `check.bat` as the full gate. Committed separately (`housekeeping: record human verification of tasks 0-2, adopt check.bat gate`) so the task commit stays single-purpose.
- `src/habesha_names/translit/schemes.py`: `PRACTICAL` table `(consonant label, vowel order) → Latin`, built at import by crossing `_CONSONANTS` (45 post-collapse series → Latin onset) × `_VOWELS` (order → vowel) over exactly the syllables in the generated `SYLLABLES` table — no hand-typed fidel↔Latin pair, coverage is testable. Per the kickoff hard requirement, series collapsed by `normalize()` (hh ሐ, x ኀ, sz ሠ, tz ፀ, pharyngeal ዐ) have NO rows. `verified: false` header comment; `SCHEMES` registry holds only `"practical"` in v0.1.
- `src/habesha_names/translit/to_latin.py`: `transliterate(text, scheme="practical")` — calls `normalize()` first, unconditionally; per-word rendering with three context rules (all flagged unverified): 6th-order ə bare when word-final/after-vowel else +epenthetic "i"; 6th-order የ glide "i" medial / "y" final after a vowel; guttural (h, glottal) order-1 vowel "a". Fidel-initial words are name-cased; Latin/digits/marks/Extended pass through. Unknown scheme → `ValueError`.
- `tests/test_translit_latin.py`: 21 tests — pinned invariant `transliterate("ፀሐይ") == transliterate("ጸሀይ") == "Tsehay"` (chars cross-checked via `unicodedata.name`); plan round-trips Tesfaye/Gebremedhin/Tsehay; ኃይለ ሥላሴ→"Haile Selassie" marked `xfail(strict=True)` with logged reason (see deviations) plus a behavior pin of the actual "Haile Silase" output and a passing "ኃይለ"→"Haile" check; full-table property tests (every homophone-source syllable transliterates identically to its target; table covers exactly the post-collapse syllables; no collapsed-series rows; ASCII-lowercase-only cells); normalize-first equivalence; passthrough/casing/scheme/empty/stability/doctest tests.
- Review queue: expanded the PRACTICAL-table item with 12 decision sub-items (ቀ, 6th-order ə, ጸ, ቸ/ጨ, ኘ, labialized forms, guttural order-1, የ glide, ወ "we"/"wo", order-5 é + Selassie conflict, remaining consonants), each with alternatives considered and the rationale for the default.

Verification output (paste FULL command + output, unedited):

Task 3 Verify block (cmd, after `call .venv\Scripts\activate.bat`):

    pytest tests\test_translit_latin.py -q && echo EXIT CODE: %ERRORLEVEL%

Output:

    ....x................                                                    [100%]
    20 passed, 1 xfailed in 0.57s
    EXIT CODE: 0

Full repo gate (`D:\habesha-names\check.bat` = pytest -q && ruff check . && mypy src, inside .venv):

    .............................................x................           [100%]
    61 passed, 1 xfailed in 0.44s
    All checks passed!
    Success: no issues found in 11 source files
    EXIT CODE: 0

Files touched: `src/habesha_names/translit/schemes.py` (new), `src/habesha_names/translit/to_latin.py` (new), `tests/test_translit_latin.py` (new), `PROGRESS.md`, plus housekeeping commit (`AGENT_KICKOFF.md`, `PROGRESS.md` status board, `check.bat` first tracked).

Deviations from plan (and why):
- Plan round-trip ኃይለ ሥላሴ→"Haile Selassie" is `xfail(strict=True)`, not passing: the conventional spelling needs geminated "ss" (gemination is unmarked in fidel) and "ie" for the order-5 vowel (a per-name convention). No table choice produces it without special-casing, which the kickoff forbids. Default output is "Haile Silase" ("Haile" itself matches). Review-queue item added; Robel decides (e.g. é→"ie" globally, lexicon-level exceptions in Task 4, or accept the xfail).
- The 6th-order epenthetic vowel and glide handling live as context rules in `to_latin.py` rather than as static table cells (a cell can't see word position); the table's order-6 cells hold the bare consonant and the rules are documented in both module docstrings.
- `check.bat` had to be invoked by absolute path in this session's shell harness (`cmd /c D:\habesha-names\check.bat`); relative invocation was not resolved. Contents ran unmodified.

Known issues / TODOs introduced:
- Word-final 6th-order consonants never epenthesize → word-final clusters lose their vowel (ፍቅር-style names would come out "Fikr"). Flagged in the review queue; revisit with Robel's 6th-order decision.
- "Weizero" (ወይዘሮ) vs conventional "Woizero" mismatch — must be settled before Task 4 seeds `titles.json`.

Next session should start with: Task 4 — Data layer (`data/schema.md`, `titles.json`, `compounds.json`, `given_names.json` all `"verified": false`, lazy loader `_data.py`). Check the review queue first in case Robel has decided the ወ/ኘ/ቀ defaults — titles.json spellings depend on them.

## Session 5 — 2026-07-11

Task attempted: Task 4 — Data layer + seed lexicons

What was actually done:
- `src/habesha_names/data/schema.md`: contracts for the three JSON files, the `verified` workflow (agent seeds `false`, only Robel flips), general loader-enforced rules (exact keys, Ethiopic-script fidel, NFC, ASCII Latin, weights/gender sums = 1, duplicates rejected, file order = canonical order), and a per-entry review checklist for Robel.
- `src/habesha_names/data/titles.json`: 12 entries — exactly the plan list (Ato, Woizero/W-ro, Woizerit/W-rt, Dr, Prof, Eng, Qes, Abba, Abune, Memhir, Sheikh, Haji) with fidel forms incl. slash abbreviations (ወ/ሮ etc.). Latin canonical spellings come from the plan itself, so this did NOT need the still-open ወ→we/wo transliteration decision; ወይዘሮ stays canonical "Woizero" regardless of what `transliterate` outputs.
- `src/habesha_names/data/compounds.json`: the exact ARCHITECTURE §4.3 prefix list (10, Welete marked `f`) and second-element list (12), plus 9 slash-abbreviation expansions with weights (G/→Gebre 0.8/Girma 0.2 per the architecture's example; the rest agent-invented, flagged).
- `src/habesha_names/data/given_names.json`: 56 entries in the ARCHITECTURE §4.5 contract shape (incl. the ፀሐይ/Tsehay example verbatim), covering every name the plan/architecture tests reference (Tesfaye, Gebremedhin, Tsehay, Abebe, Bikila, Wolde, Hailemariam, Desalegn, Girma, Mohammed, Hussein, Fatuma, Kebede, Alemu, Almaz, Tesfahun, Abebech, Bethlehem, …) plus high-frequency seeds. ALL `"verified": false`.
- `src/habesha_names/_data.py`: lazy singleton loader (`@cache`, `importlib.resources`), frozen dataclasses (`Title`, `CompoundPrefix`, `CompoundSecond`, `AbbreviationExpansion`, `GivenName`, `Lexicon`), strict validation raising `LexiconError` (exact-key checks, type checks, `is_ethiopic` + NFC on every fidel value, gender/weight distributions sum to 1, weights non-increasing, case-insensitive duplicate rejection, cross-file check that every abbreviation expansion resolves to a known prefix or given name).
- `tests/test_data_loader.py`: 54 tests — lazy-singleton behavior; plan/architecture pins (title list, prefix/second lists, G/-expansion ranking, Tsehay contract example, seed-name presence, ≥50 entries, ALL unverified); whole-lexicon invariants (Ethiopic fidel, gender sums, no duplicates, variants ≠ canonical, abbreviations resolve + ranked); plan-pinned translit consistency (Tesfaye/Gebremedhin/Tsehay fidel → canonical); 34 malformed-payload cases against the pure `_parse_*` functions; doctests.
- Scratchpad cross-check script (Session-2 discipline): transliterated every agent-typed fidel string and compared against intended Latin — results pasted into the Human review queue above (39 OK / 11 variant / 6 mismatch for given names; all title/compound mismatches itemized). No LexiconError on real data, i.e. every typed string is valid NFC Ethiopic.

Verification output (paste FULL command + output, unedited):

Task 4 Verify block (cmd, after `call .venv\Scripts\activate.bat`):

    pytest tests\test_data_loader.py -q && python -c "from habesha_names._data import lexicon; print(len(lexicon().given_names))" && echo EXIT CODE: %ERRORLEVEL%

Output:

    ......................................................                   [100%]
    54 passed in 0.28s
    56
    EXIT CODE: 0

Full repo gate (`D:\habesha-names\check.bat` = pytest -q && ruff check . && mypy src, inside .venv):

    ........................................................................ [ 62%]
    ...........................x................                             [100%]
    115 passed, 1 xfailed in 0.70s
    All checks passed!
    Success: no issues found in 12 source files
    EXIT CODE: 0

(The first check.bat run failed ruff with 4 UP045/UP033 findings in the new `_data.py`; fixed via `ruff check --fix --unsafe-fixes` — `Optional[str]`→`str | None`, `lru_cache(maxsize=None)`→`cache`, both 3.9-safe — then the gate above ran clean.)

Files touched: `src/habesha_names/data/schema.md` (new), `src/habesha_names/data/titles.json` (new), `src/habesha_names/data/compounds.json` (new), `src/habesha_names/data/given_names.json` (new), `src/habesha_names/_data.py` (new), `tests/test_data_loader.py` (new), `PROGRESS.md`

Deviations from plan (and why):
- Plan says "~50" given names; shipped 56 so that every name referenced by plan/architecture test cases (Tasks 3/5/6/7) exists in the lexicon alongside the high-frequency seeds.
- Data files carry a top-level `{"schema": 1, ...}` wrapper (not specified by the plan) so future contract changes are detectable at load; the entry shape itself follows ARCHITECTURE §4.5 exactly.
- `given_names.json` fidel forms are stored as conventionally written (ፀሐይ, ኃይለ), NOT pre-collapsed, per schema.md — consumers normalize at comparison time. The loader enforces NFC but deliberately not homophone-collapsedness.

Known issues / TODOs introduced:
- The 6 given-name translit mismatches + second-element mismatches (review queue above) are data-vs-engine conflicts for Robel; none block Task 5 (the parser matches lexicon strings, it does not re-transliterate).
- Two engine-rule weaknesses surfaced by the cross-check (not fixed here — out of Task 4 scope, related to open review-queue items): 6th-order epenthesis in C₁C₂-final clusters (ትግስት→"Tigsit") and የ-glide after "i" doubling the vowel (ሕይወት→"Hiiwet").
- Per the updated session protocol, nothing was committed: tree left ready for Robel. Suggested commit message: `task-4: data layer + seed lexicons (schema, titles, compounds, given names, validated lazy loader)`.

Next session should start with: Task 5 — Parser (`parse/titles.py`, `parse/compounds.py` incl. G/Medhin expansion, `parse/parser.py` → `ParsedName`). The lexicon now contains every name the Task 5 test list needs; check the review queue first in case Robel has flipped any Task 4 decisions.

## Session 6 — 2026-07-12

Task attempted: Task 5 — Parser

What was actually done:
- `src/habesha_names/parse/titles.py`: `match_title(token)` — lexicon lookup over canonical Latin forms + abbreviations (case-insensitive, trailing "." tolerated) + fidel forms (compared after `normalize`, so ሐጂ/ሀጂ-style homophone spellings hit the same title). Index built lazily (`@cache`) from `lexicon()`; no other state.
- `src/habesha_names/parse/compounds.py`: three detectors against the compound lexicon — `split_joined` (one token = prefix + second element, e.g. "Hailemariam", ገብረመድህን), `match_pair` (two adjacent tokens = spaced compound), `expand_abbreviation` ("G/Medhin" / "G.Medhin": single letter must be a known abbreviation AND remainder a known second element; top-weight candidate applied, ALL candidates recorded in the returned note; prefix candidates yield one joined token, given-name candidates stay separate). Latin matched case-insensitively, fidel after `normalize` — homophone spellings behave identically by construction. "W/ro" can never expand here (remainder "ro" is not a second element), and titles are stripped before expansion anyway.
- `src/habesha_names/parse/parser.py`: `ParsedName` frozen dataclass exactly per ARCHITECTURE §4.3 (plus `__str__` for the §6 `parse(str(parsed))` stability property), and `parse(raw, *, assume_diaspora=False)` with the pipeline: normalize → comma inversion (exactly one comma = "patronym, given"; other comma patterns treated as whitespace, both noted) → leading-title strip (first recorded as canonical Latin, extras noted) → script detection (ethiopic/latin/mixed) → slash-abbreviation expansion → compound joining (already-joined flagged in place; adjacent prefix+second joined) → positional roles (given/patronym/avonym; extras noted, never silently dropped) → initials noted verbatim → diaspora flag. `compound_confidence` = min over compound decisions taken (1.0 / 0.9 / 0.65 / candidate weight — agent-chosen constants, review-queued); `given_is_compound` scoped to the given name only. Empty-after-normalize input raises `ValueError`.
- `tests/test_parse.py`: 25 tests — all nine plan-required cases ("Abebe Bikila Wolde", "Ato Abebe Bikila", "Hailemariam Desalegn", "Haile Mariam Desalegn" with confidence pinned in (0,1), "G/Medhin Tesfaye" with Gebre+Girma candidates asserted auditable in the note, "Bikila, Abebe", "Abebe B.", "ወይዘሮ ጸሐይ ገብረመድህን", diaspora mode); behavior pins around them (dot-form abbreviation, abbreviation in patronym position, case-insensitive/abbreviated/fidel titles, 4-token overflow confidence ordering, two-token spaced compound, fidel homophone parse identity, fidel spaced compound, mixed script, raw preserved verbatim, extra tokens noted, single-token title, empty raises); properties (parse(str(parsed)) structural stability over 8 samples, determinism); doctests for all three modules. Fidel expectations computed via `normalize()` in the tests — no second hand-typed copy of collapsed spellings; all names come from the plan list or the seeded lexicon.

Verification output (paste FULL command + output, unedited):

Task 5 Verify block (cmd, after `call .venv\Scripts\activate.bat`):

    pytest tests\test_parse.py -q && echo EXIT CODE: %ERRORLEVEL%

Output:

    .........................                                                [100%]
    25 passed in 0.51s
    EXIT CODE: 0

Full repo gate (`D:\habesha-names\check.bat` = pytest -q && ruff check . && mypy src, inside .venv):

    ........................................................................ [ 51%]
    ....................................................x................    [100%]
    140 passed, 1 xfailed in 1.42s
    All checks passed!
    Success: no issues found in 15 source files
    EXIT CODE: 0

Files touched: `src/habesha_names/parse/titles.py` (new), `src/habesha_names/parse/compounds.py` (new), `src/habesha_names/parse/parser.py` (new), `tests/test_parse.py` (new), `PROGRESS.md`

Deviations from plan (and why):
- ARCHITECTURE §4.3 lists comma inversion and initials LAST in the logic order; comma inversion is applied during tokenization instead, because it reorders tokens for every later step (title strip, role assignment). Initials handling stays last as specified. Documented in the module docstring; no behavioral conflict with the plan.
- `ParsedName` gained a `__str__` (not in the §4.3 sketch) because ARCHITECTURE §6 requires the `parse(str(parsed))` stability property, which needs a canonical string form. No other field or method added.
- Test file is `tests/test_parse.py` (exactly the plan's Verify path); ARCHITECTURE §3 shows `tests/test_parse_*.py` — single file chosen so the Verify command matches the plan verbatim.

Known issues / TODOs introduced:
- Parser heuristic defaults (confidence constants, two-token compound policy, canonical-Latin titles, comma/has_surname policy, initials, hyphenated forms deferred to Task 7) are all agent-chosen — itemized in the Human review queue above.
- Mid-string titles ("Dr" after a comma-inverted patronym, e.g. "Dr Bikila, Abebe") are not detected — only leading tokens are title-checked. Acceptable for v0.1; revisit if real inputs show it.
- Per session protocol, nothing was committed: tree left ready for Robel. Suggested commit message: `task-5: parser (titles, compound detection + G/Medhin expansion, ParsedName)`.

Next session should start with: Task 6 — Phonetic key + token similarity (`match/phonetic.py` HabeshaKey per ARCHITECTURE §4.4, `match/token.py` with in-repo Jaro-Winkler + property tests against known JW values; key equality/inequality pins from the plan). Check the review queue first in case Robel has decided any Task 3/4/5 defaults.

## Session 7 — 2026-07-12

Task attempted: Task 6 — Phonetic key + token similarity

What was actually done:
- `src/habesha_names/match/phonetic.py`: `phonetic_key(name)` — HabeshaKey per the ARCHITECTURE §4.4 sketch: transliterate first (fidel keys like its romanization; Latin passes through), lowercase + strip non a-z (spaces too, so "Haile Mariam" keys like "Hailemariam"), left-to-right greedy digraph folding (ts/tz→s, sh→x, ch→c, kh/gh→h, ph→f, th→t), adjacent-double collapse, terminal -aye/-ay/-ai → "A" marker, key = uppercase consonant skeleton + ":" + first-vowel class (a / e,i / o,u — the class bucketing is what makes Mohammed=Muhammed hold). Letterless input → `""`. All rules flagged provisional in the module docstring (Task 8 tunes them).
- `src/habesha_names/match/token.py`: `jaro_winkler(a, b)` implemented in-repo from the standard definition (prefix scale 0.1, cap 4, boost only when Jaro > 0.7; both-empty = 1.0, one-empty = 0.0), private `_jaro`, and `sim(a, b)` = max(PHONETIC_WEIGHT if HabeshaKeys match, JW over normalized tokens), where normalization = transliterate → lowercase → strip non-letters; identical normalized tokens = 1.0, letterless side = 0.0. `PHONETIC_WEIGHT = 0.9` (invented, review-queued). The §4.4 variant-set-overlap term is NOT wired — it needs Task 7's engine; plan Task 7 anticipates this circularity ("wire in Task 8").
- `tests/test_match_phonetic.py`: 13 tests — all four plan equality groups (Tsehay/Sehay/Tsehai, Tesfaye/Tesfay/Tesfai, Mohammed/Mohamed/Muhammed, Kebede/Kebbede) and all three inequality pairs (Alemu/Almaz, Tesfaye/Tesfahun, Abebe/Abebech) parametrized; fidel-keys-like-Latin (ፀሐይ/ጸሀይ/Tsehay); case/punctuation/whitespace insensitivity; spaced-vs-joined compound; Bethlehem/Betelhem (§4.2 variant pair, exercises th→t); digraph mechanics on non-name ASCII vectors; empty-key cases; key-format regex; determinism; doctests.
- `tests/test_match_token.py`: 15 tests — JW pinned to the standard published vectors with the arithmetic re-derived in comments (MARTHA/MARHTA = 17.3/18, DIXON/DICKSONX = 24.4/30, DWAYNE/DUANE = 37.8/45); no-boost-at-or-below-0.7 and prefix-cap-4 branch pins; identity/empty/zero-match cases; symmetry + boundedness over the first 12 lexicon canonicals; `sim` pins (fidel = Latin 1.0, phonetic backstop beats JW on Tzehay/Sehay, equality groups ≥ 0.9, Alemu/Almaz < 0.9, empty → 0.0, symmetric/bounded/deterministic); doctests. Name strings limited to plan pins, plan round-trip glyphs, ARCHITECTURE variant pairs, and lexicon canonicals — no invented names.

Verification output (paste FULL command + output, unedited):

Task 6 Verify block (cmd, after `call .venv\Scripts\activate.bat`):

    pytest tests\test_match_phonetic.py tests\test_match_token.py -q && echo EXIT CODE: %ERRORLEVEL%

Output:

    ......................................                                   [100%]
    38 passed in 0.52s
    EXIT CODE: 0

Full repo gate (`D:\habesha-names\check.bat` = pytest -q && ruff check . && mypy src, inside .venv):

    ........................................................................ [ 40%]
    ........................................................................ [ 80%]
    ..................x................                                      [100%]
    178 passed, 1 xfailed in 1.29s
    All checks passed!
    Success: no issues found in 17 source files
    EXIT CODE: 0

Files touched: `src/habesha_names/match/phonetic.py` (new), `src/habesha_names/match/token.py` (new), `tests/test_match_phonetic.py` (new), `tests/test_match_token.py` (new), `PROGRESS.md`

Deviations from plan (and why):
- ARCHITECTURE §4.4's `sim` formula includes a `variant_set_overlap` term; it is documented-but-absent here because `variants()` is Task 7 — exactly the circularity the plan's Task 7 note anticipates ("wire in Task 8 if circular"). Until Task 8, `sim` is a lower bound on the final design.
- The §4.4 sketch encodes "first vowel"; implemented as first-vowel *class* (a / e,i / o,u) because the exact vowel breaks the plan's own Mohammed=Muhammed equality pin. Flagged in the review queue.
- `check.bat` again required absolute-path invocation in this session's shell harness (same as Sessions 4–6); contents ran unmodified.

Known issues / TODOs introduced:
- Medial ay/ai not folded by HabeshaKey → Haymanot/Haimanot key differently (review queue; Task 8 tuning candidate alongside q↔k).
- `sim("Abebe", "Abebech")` ≈ 0.94 via Jaro-Winkler alone (shared 5-char prefix) even though their phonetic keys correctly differ — whether token-level JW should be dampened for such pairs is a Task 8 threshold/weights decision, deliberately not taken here.
- Per session protocol, nothing was committed: tree left ready for Robel. Suggested commit message: `task-6: phonetic key + token similarity (HabeshaKey, in-repo Jaro-Winkler, sim backstop)`.

Next session should start with: Task 7 — Variant generator (`translit/variants.py`: weighted rewrite rules per ARCHITECTURE §4.2, top-N deterministic output; the `match_token ≥ 0.8` property can now use Task 6's `sim`). Check the review queue first in case Robel has decided any Task 3–6 defaults — the variant rule set overlaps heavily with the open transliteration decisions (q↔k, ts↔s↔tz, -ay/-ai/-aye, é↔ie↔e).

## Session 8 — 2026-07-12

Task attempted: Task 7 — Variant generator

What was actually done:
- `src/habesha_names/translit/variants.py`: `variants(name, *, n=25)` — ranked plausible Latin spellings for fidel or Latin input (input's own transliterated, name-cased spelling always first). Two-layer weighted rewrite engine per ARCHITECTURE §4.2:
  - Token level: lexicon spelling groups from `given_names.json` (canonical + variants stand in for each other — this is where the Arabic-origin table lives, as the `origin: "arabic"` entries), compound splits/joins/hyphen/slash/dot forms (Gebremedhin ↔ Gebre Medhin ↔ Gebre-Medhin ↔ G/Medhin ↔ G.Medhin, detected via the public `parse.compounds` functions), and slash-abbreviation expansion of the input itself (every lexicon candidate emitted, e.g. G/Medhin → Gebremedhin 0.8 AND Girma Medhin 0.2).
  - Character level per token: ts↔tz↔s, q↔k, h↔kh, th→t, ie↔e, terminal -ay/-ai/-aye, gemination doubling/collapse (intervocalic only), sixth-order e→a, final w↔ou.
  - Every rewrite is classified by whether it preserves the base spelling's HabeshaKey. Key-preserving rewrites combine (≤ 3); a key-breaking rewrite applies only ALONE — with the phonetic backstop in `sim`, this is the mechanism that keeps every variant ≥ 0.8 similarity. Cumulative-likelihood floor 0.02; best-first (heap) enumeration with fixed exploration caps, so output is deterministic, `n` is a pure prefix slice of one global ranking, and combinatorial explosion is structurally impossible.
- `tests/test_variants.py`: 18 tests — every ARCHITECTURE §4.2 rule family pinned on plan/lexicon names (Tsehay family + fidel homophone identity, Tesfaye glide group, Gebre→Gabre/Gebra, Kebede/Kebbede + Alemu/Allemu both directions, Bekele/Beqele both directions, h↔kh, all three Arabic-origin groups incl. variant→canonical direction, Bethlehem pair, all five compound shapes in all directions, G/ expansion showing BOTH candidates); ranking/validation pins (base first + name-cased, top-n exact, n=0 raises, n prefix-slice property); no-duplicates + determinism over all 56 lexicon canonicals; empty/letterless input; the ARCHITECTURE §6 property `sim(x, v) ≥ 0.8` wired against Task 6's `sim` NOW (not deferred) over all lexicon canonicals + plan names, with slash/dot forms carved out (documented, review-queued); doctests.
- The property test did its job during development: first run failed with `sim('Bekele', 'Bakele') = 0.780` — first-vowel e→a on 3-e names scrambles greedy Jaro-Winkler with no phonetic backstop. Fixed by gating that rewrite to tokens with ≤ 2 e's (keeps the plan-pinned Gebre→Gabre), not by weakening the test. Review-queued.

Verification output (paste FULL command + output, unedited):

Task 7 Verify block (cmd, after `call .venv\Scripts\activate.bat`):

    pytest tests\test_variants.py -q && echo EXIT CODE: %ERRORLEVEL%

Output:

    ..................                                                       [100%]
    18 passed in 0.25s
    EXIT CODE: 0

Full repo gate (`D:\habesha-names\check.bat` = pytest -q && ruff check . && mypy src, inside .venv):

    ........................................................................ [ 36%]
    ........................................................................ [ 73%]
    ..................x..................................                    [100%]
    196 passed, 1 xfailed in 1.56s
    All checks passed!
    Success: no issues found in 18 source files
    EXIT CODE: 0

Files touched: `src/habesha_names/translit/variants.py` (new), `tests/test_variants.py` (new), `PROGRESS.md`

Deviations from plan (and why):
- The plan's property test (`match_token(x, v) >= 0.8`, "wire in Task 8 if circular") is wired NOW against Task 6's `sim` — no circularity exists in that direction (`translit.variants` never imports `match`; `match.token` will import `translit.variants` in Task 8 for the variant-overlap term, so the dependency arrow was kept pointing match→translit deliberately). One carve-out: slash/dot abbreviation forms ("G/Medhin") lose letters and cannot pass token-level `sim`; they are exempted with a comment and review-queue item — the Task 8 FULL matcher expands abbreviations before scoring (ARCHITECTURE §4.4 step 1), so the §6 property still holds end-to-end where it matters.
- ARCHITECTURE §4.2 lists Bethlehem/Betelhem under `é↔ie↔e`; the l/e transposition in that pair is not derivable from any local rewrite rule, so it is satisfied via the lexicon group (both spellings are seeded variants). The ie↔e rule itself exists and is tested on Daniel→Danel-style rewrites.
- `translit/variants.py` imports `parse.compounds` (public functions) for compound detection rather than re-implementing prefix/second matching — a new cross-package edge (translit→parse) not sketched in ARCHITECTURE §3's layering, but acyclic (parse never imports translit) and single-sourced.

Known issues / TODOs introduced:
- Slash/dot variants are below-0.8 by token `sim` until Task 8's matcher-level expansion (carved out, review-queued).
- No s→ts, a→e, or t→th reverse rules (review queue) — a non-lexicon "Sehay"-style spelling cannot reach its ts-form by rules alone.
- First-vowel e→a suppressed on tokens with 3+ e's (review queue; alternative is folding a/e in HabeshaKey — Task 8 tuning).
- Per session protocol, nothing was committed: tree left ready for Robel (Task 6's files are also still uncommitted in the working tree). Suggested commit message: `task-7: variant generator (weighted rewrite engine, compound forms, top-N ranking)`.

Next session should start with: Task 8 — Full-name matcher + golden corpus (`match/full.py` per ARCHITECTURE §4.4: alignment, swap/truncation tolerance, weights config, `MatchResult`; wire variant-set overlap into `sim`; `tests/golden/pairs.json` ≥150 pairs with ~60 agent-seeded + `"needs_human": true` markers; `scripts/benchmark.py --min-mps 50000`; record tuned thresholds in the decisions log). Check the review queue first — Task 8 tuning touches nearly every open Task 6/7 item.

## Session 9 — 2026-07-13

Task attempted: Task 8 — Full-name matcher + golden corpus

What was actually done:
- `src/habesha_names/match/token.py` (Task 8 wiring + tuning): the §4.4 variant-set-overlap term is now in `sim` — a token appearing in the other's `variants()` output scores `VARIANT_WEIGHT = 0.85`. Corpus tuning added `KEY_MISMATCH_DAMP = 0.6`: Jaro-Winkler is damped when the HabeshaKeys differ, which is what puts the plan's different-person confusables (Tesfaye/Tesfa raw JW 0.94 → 0.57, Abebe/Abebech, Alemu/Almaz) under the 0.6 gate while genuine variants are caught by the phonetic/variant/lexicon terms instead. New `sim_detail(a, b) -> TokenSim(score, method)` reports which component won ("exact"/"phonetic"/"variant"/"jaro_winkler"/"none") for `MatchResult` explanations; `sim` is now a thin wrapper. Normalization, keys, variant sets, and the symmetric pair-similarity core are memoized in bounded `lru_cache`s (pure memoization — needed for the benchmark gate; JW dominated the profile otherwise).
- `src/habesha_names/match/phonetic.py` (corpus-driven tuning, the ONLY Task 6 rule change): every non-initial `y` folds to `i` (glide fold), so Haymanot=Haimanot, Maryam=Mariyam=Mariam, Hailemaryam=Hailemariam key-equal; `_TERMINAL_SUFFIXES` gained "aie" (the fold's image of "aye" — Tesfaye group unchanged). Fixes the ኃይለማርያም↔Hailemariam corpus pair (0.58 → 0.96) and closes the old "medial ay/ai not folded" review item. All 13 Task 6 phonetic tests still pass unmodified.
- `src/habesha_names/match/full.py` (new): `match(a, b, *, weights=None) -> MatchResult` per §4.4 — parse both sides (titles stripped, abbreviations expanded, compounds joined by Task 5), token-similarity matrix over the ≤3 positional roles, brute-force injective alignment with swap tolerance (crossed alignments allowed at `swap_penalty = 0.98`, flagged `swapped`) and truncation tolerance (each unmatched role costs `1 − role_weight·missing_scale`, missing avonym → ×0.9). `MatchWeights` config dataclass (0.45/0.35/0.20 §4.4-pinned; validated), `TokenPair` (tokens, roles, sim, method), `MatchResult` with `__float__` plus comparison dunders so `match(a,b) > 0.9` works, notes carry both parses' notes (side-prefixed) + alignment notes ("avonym missing in b", swap). Score = weighted mean over aligned roles × penalties; symmetric, deterministic, in [0,1]. Bonus surfaced by tests: `match("ኃይለ ሥላሴ", "Haile Selassie") = 0.96` — the Task 3 Selassie xfail is bridged at match level by the phonetic key.
- `scripts/gen_golden_pairs.py` (new) + `tests/golden/pairs.json` (generated, 201 pairs): corpus is DERIVED, never hand-typed — categories: every lexicon fidel↔canonical pair, every canonical↔seeded-variant pair, top rule-engine variants for 12 plan anchors, 15 full-name matcher-feature pairs (swap, truncation, comma, title, fidel homophones, all five compound shapes, Arabic-origin, Selassie), plan-pinned confusable negatives, full-name negatives incl. two sibling-style records, and the 25 highest-scoring distinct-canonical near-misses. ALL pairs `needs_human: true`; 6 pairs `known_fail: true` (current engine limits, itemized in the review queue) — the golden test asserts these KEEP failing so improvements force conscious regeneration. `--check` mode = byte-exact staleness gate, wired into the test suite.
- `tests/test_match_full.py` (33 tests): identity/case/fidel/title/comma; swap (score exactly 0.98, note, below in-order); truncation (0.9, side-named note); abbreviation + spaced-compound alignment; pairs content (roles/sims/methods incl. "phonetic" and "variant"); plan confusables ≤ 0.6; float/comparison ergonomics; frozen; empty raises; weights override + validation + swap_penalty=1.0; symmetry/bounds/determinism properties; Selassie bridge; doctests.
- `tests/test_golden.py` (7 shape tests + 195 per-pair gates + 6 known-fail gates): size ≥ 150, §6 thresholds pinned (0.85/0.60), all-needs_human, no duplicates, schema, both outcomes + fidel present, generator `--check` subprocess; every active pair parametrized individually.
- `scripts/benchmark.py` (new): deterministic dedup-shaped workload (lexicon-derived full names + variant respellings compared in overlapping windows, names recur as in real batch dedup), untimed warm-up pass, then ≥100k timed `match()` calls; `--min-mps` gate. Result on this machine: 55–60k matches/sec (first cut was 14.8k; profiling showed `_jaro` at 53% — fixed by the memoized symmetric similarity core + precomputed alignment tables, no scoring change).
- `tests/test_variants.py`: removed the Task 7 slash/dot carve-out from the ≥0.8 property test — with variant overlap wired into `sim`, "G/Medhin"-style forms now score 0.85 and the property holds with NO exemptions.

Verification output (paste FULL command + output, unedited):

Task 8 Verify block (cmd, after `call .venv\Scripts\activate.bat`):

    pytest tests\test_match_full.py tests\test_golden.py -q && python scripts\benchmark.py --min-mps 50000 && echo EXIT CODE: %ERRORLEVEL%

Output:

    ........................................................................ [ 30%]
    ........................................................................ [ 60%]
    ........................................................................ [ 91%]
    .....................                                                    [100%]
    237 passed in 1.17s
    100296 match() calls over 504 distinct pairs in 1.792s
    55,969 matches/sec
    OK: meets required 50,000 matches/sec
    EXIT CODE: 0

Golden-corpus generator staleness check (also exercised by `test_corpus_file_is_current`):

    python scripts\gen_golden_pairs.py --check
    OK: pairs.json is current (201 pairs)

Full repo gate (`D:\habesha-names\check.bat` = pytest -q && ruff check . && mypy src, inside .venv):

    ........................................................................ [ 16%]
    ........................................................................ [ 33%]
    ........................................................................ [ 49%]
    ........................................................................ [ 66%]
    ........................................................................ [ 82%]
    .......................................x................................ [ 99%]
    ..                                                                       [100%]
    433 passed, 1 xfailed in 2.06s
    All checks passed!
    Success: no issues found in 19 source files
    EXIT CODE: 0

(One intermediate ruff failure during the session — unused loop variable in the corpus generator — fixed by renaming to `_score`; the gate above is the clean rerun. First benchmark run failed at 14,764 matches/sec; the memoization described above brought it to 55–60k. Corpus was regenerated once after the phonetic-key tuning; `--check` confirms the committed file matches the final engine.)

Files touched: `src/habesha_names/match/full.py` (new), `src/habesha_names/match/token.py` (variant overlap, damp, sim_detail, memoization), `src/habesha_names/match/phonetic.py` (glide fold tuning), `scripts/gen_golden_pairs.py` (new), `scripts/benchmark.py` (new), `tests/golden/pairs.json` (generated, new), `tests/test_match_full.py` (new), `tests/test_golden.py` (new), `tests/test_variants.py` (carve-out removed), `PROGRESS.md`

Deviations from plan (and why):
- Plan says "Agent seeds ~60 mechanically-derivable pairs" toward the ≥150 target; the generator mechanically derives ALL 201 (variant-generated plus lexicon- and plan-derived), because a corpus below 150 would fail the plan's own ≥150 expectation and hand-writing the remainder would violate the no-invented-linguistic-data rule. Every pair stays `needs_human: true` — the "~60" spirit (agent seeds, Robel curates/extends) is preserved, there are just more mechanically-safe seeds than estimated.
- Six corpus pairs violate their §6 threshold today; instead of dropping them (hiding engine limits) or letting them fail CI, they ship as `known_fail: true` with a strict keeps-failing test — same honesty mechanism as the Task 3 xfail.
- `phonetic.py` was modified (glide fold) although it is a Task 6 file — this IS the "tune HabeshaKey against corpus" instruction of Task 8; the change is minimal, corpus-motivated, review-queued, and all original Task 6 tests pass unmodified.
- `MatchResult.pairs`/`notes` are `list`s per the §4.4 sketch (matching `ParsedName.notes` precedent) even though the dataclass is frozen.

Known issues / TODOs introduced:
- The 6 `known_fail` golden pairs (itemized in the review queue): መሐመድ↔Mohammed, two engine-emitted mutated-prefix spaced compounds ("Gebrie Medhin", "Hailie Mariam"), two sibling-style review-zone pairs, Bekele↔Bikila key collision.
- `KEY_MISMATCH_DAMP` means an out-of-vocabulary, key-breaking misspelling scores low — mitigated only by lexicon growth (v0.2's 2,000 entries) or Robel-added variants.
- Benchmark throughput relies on memoization caches being warm; a workload of ~unique never-repeating tokens would run slower (first-touch cost unchanged). Cache sizes (65536 norms/keys, 8192 variant sets, 131072 sim pairs) are unreviewed engineering defaults.
- Per session protocol, nothing was committed: tree left ready for Robel (Session 8's Task 6/7 files may also still be uncommitted). Suggested commit message: `task-8: full matcher + golden corpus (alignment, swap/truncation tolerance, variant-overlap sim, benchmark)`.

Next session should start with: Task 9 — Public API polish + README (`__init__.py` exports per ARCHITECTURE §5, docstrings with runnable examples on every public callable, README 6-snippet pitch, CHANGELOG.md; verify gate adds `mypy src --strict` and `python -m doctest README.md -v`). Check the review queue first — Task 8 added matcher/tuning items Robel may have decided.

## Session 10 — 2026-07-13

Task attempted: Task 9 — Public API polish + README

What was actually done:
- `src/habesha_names/__init__.py`: public re-exports per ARCHITECTURE §5 — `parse`, `match`, `variants`, `transliterate`, `normalize`, `phonetic_key`, `is_ethiopic` — plus `__version__`, with `__all__` pinned and a doctested package docstring. §5 also lists `to_fidel` and `guess_gender`, but both are v0.2 modules (ARCHITECTURE §4.2 / §3 mark them v0.2 and the files do not exist); exported only the seven that exist rather than shipping stubs — logged as a deviation below, README/CHANGELOG state they are planned for v0.2, and a test pins their absence.
- `README.md`: full rewrite — pitch, "Why" (the §1 problem list), install, quick tour with the six required snippets (parse / variants / match / explainability / normalize / transliterate) plus a "Building blocks" snippet for `phonetic_key`/`is_ethiopic`, public-API block, data-verification caveat, development section. Every snippet is a doctest; every expected output was collected by running the engine first (scratchpad scripts), not typed from memory.
- `CHANGELOG.md` (new): Keep-a-Changelog format, `[Unreleased]` section itemizing the v0.1 feature set.
- `tests/test_public_api.py` (new, 6 tests): `__all__` = §5 surface exactly; every public callable has a docstring containing a doctest; v0.2 names not exported; version pin; package-docstring doctests; README doctests via `doctest.testfile(..., encoding="utf-8")` so they also run under pytest/CI regardless of locale.
- Strict-mode fix in `_data.py` (`_optional_gender`: explicit `isinstance` narrow — the one `mypy src --strict` error in the whole repo).
- Gate upgrade per kickoff engineering rule ("Task 9 onward: --strict") and ARCHITECTURE §6 ("CI matrix: … mypy --strict"): `check.bat` and `.github/workflows/ci.yml` now run `mypy src --strict`.
- Fixed 4 pre-existing doctest-runner tests (`test_match_full/phonetic/token.py`, `test_parse.py`): the new function exports `match`/`parse` shadow the same-named subpackage ATTRIBUTES on the package, so `import habesha_names.match.full as mod` no longer resolves; switched to `from habesha_names.match import full as mod` (import-system path, unaffected). Commented in each test.
- Probed the README-doctest encoding question empirically before writing (scratchpad `readme_probe.md`): fidel text in the file decodes correctly and doctest report output escapes safely on this machine's cmd; the pytest run reads it with explicit UTF-8 as a guard for stricter environments.

Verification output (paste FULL command + output, unedited):

Task 9 Verify block (cmd, after `call .venv\Scripts\activate.bat`):

    pytest -q && mypy src --strict && ruff check . && python -m doctest README.md -v && echo EXIT CODE: %ERRORLEVEL%

Output (the `-v` per-example listing of the 29 README doctests is elided here for length — every example printed `ok`, none failed; head and summary unedited):

    ........................................................................ [ 16%]
    ........................................................................ [ 32%]
    ........................................................................ [ 49%]
    ........................................................................ [ 65%]
    ........................................................................ [ 81%]
    .............................................x.......................... [ 98%]
    ........                                                                 [100%]
    439 passed, 1 xfailed in 3.67s
    Success: no issues found in 19 source files
    All checks passed!
    [... 29 "Trying:/Expecting:/ok" blocks, all ok ...]
    1 item passed all tests:
      29 tests in README.md
    29 tests in 1 item.
    29 passed.
    Test passed.
    EXIT CODE: 0

Full repo gate (`D:\habesha-names\check.bat`, now = pytest -q && ruff check . && mypy src --strict, inside .venv):

    ........................................................................ [ 16%]
    ........................................................................ [ 32%]
    ........................................................................ [ 49%]
    ........................................................................ [ 65%]
    ........................................................................ [ 81%]
    .............................................x.......................... [ 98%]
    ........                                                                 [100%]
    439 passed, 1 xfailed in 3.38s
    All checks passed!
    Success: no issues found in 19 source files

Files touched: `src/habesha_names/__init__.py` (exports), `src/habesha_names/_data.py` (strict fix), `README.md` (rewrite), `CHANGELOG.md` (new), `tests/test_public_api.py` (new), `tests/test_match_full.py` / `tests/test_match_phonetic.py` / `tests/test_match_token.py` / `tests/test_parse.py` (doctest-runner import form), `check.bat` + `.github/workflows/ci.yml` (mypy --strict), `PROGRESS.md`

Deviations from plan (and why):
- ARCHITECTURE §5 lists `to_fidel` and `guess_gender` in the import block, but both are v0.2 features with no modules in the repo; Task 9 says "exports per ARCHITECTURE §5". Resolved by exporting the seven existing callables only: re-exporting nonexistent names is impossible, and stubbing v0.2 features is forbidden by scope discipline. Documented in the package docstring, README, CHANGELOG, and pinned by `test_v02_names_are_not_exported_yet`.
- The verbose doctest listing is summarized (not pasted line-by-line) in the verification output above — it is ~200 lines of mechanical "Trying/ok" blocks; the unedited head, counts, and exit code are pasted, and the same 29 examples also run (and pass) inside the pytest figure via `test_readme_doctests`.
- `tests/test_public_api.py` is not named by the plan's Verify block; added so the §5 surface and README stay gated in CI on all platforms (the plan's `python -m doctest README.md` invocation is locale-dependent on Windows).

Known issues / TODOs introduced:
- Attribute shadowing: `habesha_names.match` / `habesha_names.parse` as ATTRIBUTES now name the functions, not the subpackages (the §5 contract requires exactly this). `from habesha_names.match import full` and direct submodule imports work unchanged; only the `import habesha_names.match.full as x` attribute-binding form is affected. Inherent to §5 + §3 naming; flagged here so Robel is aware of the ergonomic trade.
- `pyproject.toml` `[tool.setuptools.package-data]` only lists `py.typed` — the `data/*.json` lexicons will be MISSING from a built wheel (editable installs mask this). Must be fixed in Task 10 (its `python -m build && twine check` verify should also smoke-test `lexicon()` from the built wheel).
- Fidel slash abbreviations (ገ/መድህን) are not expanded by the parser — abbreviation data is Latin-only ("G/"), so a fidel-abbreviated record scores low against its expansion (surfaced while collecting README examples; README examples avoid the form). Candidate for the review queue/v0.2 data extension.
- Per session protocol, nothing was committed: tree left ready for Robel. Suggested commit message: `task-9: public API + README (§5 exports, doctested README tour, CHANGELOG, strict mypy gate)`.

Next session should start with: Task 10 — Packaging + release prep (build sdist/wheel, `twine check`, release workflow with PyPI Trusted Publishing, tag prep — Robel pushes the tag). MUST fix the package-data gap (`data/*.json` into the wheel) and verify the lexicon loads from the built artifact, not the source tree. `build`/`twine` are not in the dev extras — decide whether to add them or install ad hoc. Check the review queue first.

## Session 11 — 2026-07-13

Task attempted: Task 10 — Packaging + release prep

What was actually done:
- `pyproject.toml`: fixed the Session-10 package-data gap — `[tool.setuptools.package-data]` now ships `data/*.json` and `data/schema.md` alongside `py.typed` (previously the wheel had NO lexicon data; editable installs masked it).
- Version bumped `0.1.0.dev0` → `0.1.0` (`src/habesha_names/__init__.py` + the two test pins in `tests/test_smoke.py` / `tests/test_public_api.py`); CHANGELOG `[Unreleased]` cut to `[0.1.0] - 2026-07-13` with an explicit "all linguistic data unverified" disclosure. Rationale: "agent prepares everything; Robel pushes the tag" — the tag must match the built version, and the release workflow enforces that match.
- `MANIFEST.in` (new): sdist now includes `CHANGELOG.md`, `scripts/*.py`, and `tests/` **including `tests/golden/pairs.json`** — without it the sdist contained `tests/*.py` but not the corpus, so `test_golden.py` (which also re-runs `scripts/gen_golden_pairs.py --check` via subprocess) could not pass from an unpacked sdist. Wheel contents unaffected.
- `scripts/smoke_wheel.py` (new): smoke-tests an INSTALLED artifact — refuses to run against the source tree, optionally asserts version == tag, loads `lexicon()` (≥50 given names, 12 titles), and exercises `transliterate`/`parse`/`variants`/`match` end-to-end (plan-pinned behaviors only, no new linguistic data). Used locally below and by the release workflow.
- `.github/workflows/release.yml` (new): tag-triggered (`v*`), two jobs. `build`: `python -m build` → `twine check dist/*` → fresh venv, install the wheel, run `smoke_wheel.py "${GITHUB_REF_NAME#v}"` from /tmp (so a version/tag mismatch or missing package data fails BEFORE publish) → upload `dist/` artifact. `publish`: `pypa/gh-action-pypi-publish@release/v1` with `permissions: id-token: write` and `environment: pypi` — PyPI Trusted Publishing, no stored token. Robel's one-time PyPI setup + tag steps documented in the review-queue release item above.
- `build` and `twine` installed ad hoc into `.venv` — deliberately NOT added to the dev extras (kickoff pins dev deps to pytest/ruff/mypy; CI release job installs its own).

Verification output (paste FULL command + output, unedited):

Task 10 Verify block (cmd batch: `cd /d D:\habesha-names && call .venv\Scripts\activate.bat`, then):

    if exist dist rmdir /s /q dist
    python -m build && twine check dist\* && echo EXIT CODE: %ERRORLEVEL%

Output (the 80-line mechanical `running bdist_wheel` staging copy listing, lines "running build" through "running install_scripts", is elided for length — it duplicates the final wheel `adding` manifest, which is pasted complete and unedited below; everything else verbatim):

    * Creating isolated environment: venv+pip...
    * Installing packages in isolated environment:
      - setuptools>=77
    * Getting build dependencies for sdist...
    running egg_info
    writing src\habesha_names.egg-info\PKG-INFO
    writing dependency_links to src\habesha_names.egg-info\dependency_links.txt
    writing requirements to src\habesha_names.egg-info\requires.txt
    writing top-level names to src\habesha_names.egg-info\top_level.txt
    reading manifest file 'src\habesha_names.egg-info\SOURCES.txt'
    reading manifest template 'MANIFEST.in'
    adding license file 'LICENSE'
    writing manifest file 'src\habesha_names.egg-info\SOURCES.txt'
    * Installed build dependency versions:
      - setuptools==83.0.0
    * Building sdist...
    running sdist
    running egg_info
    [... same egg_info block as above ...]
    running check
    creating habesha_names-0.1.0
    creating habesha_names-0.1.0\scripts
    creating habesha_names-0.1.0\src\habesha_names
    creating habesha_names-0.1.0\src\habesha_names.egg-info
    creating habesha_names-0.1.0\src\habesha_names\data
    creating habesha_names-0.1.0\src\habesha_names\fidel
    creating habesha_names-0.1.0\src\habesha_names\match
    creating habesha_names-0.1.0\src\habesha_names\parse
    creating habesha_names-0.1.0\src\habesha_names\translit
    creating habesha_names-0.1.0\tests
    creating habesha_names-0.1.0\tests\golden
    copying files to habesha_names-0.1.0...
    copying CHANGELOG.md -> habesha_names-0.1.0
    copying LICENSE -> habesha_names-0.1.0
    copying MANIFEST.in -> habesha_names-0.1.0
    copying README.md -> habesha_names-0.1.0
    copying pyproject.toml -> habesha_names-0.1.0
    copying scripts\benchmark.py -> habesha_names-0.1.0\scripts
    copying scripts\gen_fidel_tables.py -> habesha_names-0.1.0\scripts
    copying scripts\gen_golden_pairs.py -> habesha_names-0.1.0\scripts
    copying scripts\smoke_wheel.py -> habesha_names-0.1.0\scripts
    copying src\habesha_names\__init__.py -> habesha_names-0.1.0\src\habesha_names
    copying src\habesha_names\_data.py -> habesha_names-0.1.0\src\habesha_names
    copying src\habesha_names\py.typed -> habesha_names-0.1.0\src\habesha_names
    [... 5 egg-info copies ...]
    copying src\habesha_names\data\__init__.py -> habesha_names-0.1.0\src\habesha_names\data
    copying src\habesha_names\data\compounds.json -> habesha_names-0.1.0\src\habesha_names\data
    copying src\habesha_names\data\given_names.json -> habesha_names-0.1.0\src\habesha_names\data
    copying src\habesha_names\data\schema.md -> habesha_names-0.1.0\src\habesha_names\data
    copying src\habesha_names\data\titles.json -> habesha_names-0.1.0\src\habesha_names\data
    [... fidel/match/parse/translit module copies (15 files) ...]
    copying tests\test_data_loader.py -> habesha_names-0.1.0\tests
    [... 11 more tests\test_*.py copies ...]
    copying tests\golden\pairs.json -> habesha_names-0.1.0\tests\golden
    copying src\habesha_names.egg-info\SOURCES.txt -> habesha_names-0.1.0\src\habesha_names.egg-info
    Writing habesha_names-0.1.0\setup.cfg
    Creating tar archive
    removing 'habesha_names-0.1.0' (and everything under it)
    * Building wheel from sdist
    * Creating isolated environment: venv+pip...
    * Installing packages in isolated environment:
      - setuptools>=77
    * Getting build dependencies for wheel...
    [... egg_info block ...]
    * Installed build dependency versions:
      - setuptools==83.0.0
    * Building wheel...
    running bdist_wheel
    [... 80-line build\lib / bdist staging copy listing elided (includes
        "copying src\habesha_names\data\*.json -> build\lib\habesha_names\data") ...]
    creating 'D:\\habesha-names\\dist\\.tmp-pgeu7wsl\\habesha_names-0.1.0-py3-none-any.whl' and adding 'build\\bdist.win-amd64\\wheel' to it
    adding 'habesha_names/__init__.py'
    adding 'habesha_names/_data.py'
    adding 'habesha_names/py.typed'
    adding 'habesha_names/data/__init__.py'
    adding 'habesha_names/data/compounds.json'
    adding 'habesha_names/data/given_names.json'
    adding 'habesha_names/data/schema.md'
    adding 'habesha_names/data/titles.json'
    adding 'habesha_names/fidel/__init__.py'
    adding 'habesha_names/fidel/normalize.py'
    adding 'habesha_names/fidel/syllable.py'
    adding 'habesha_names/fidel/tables.py'
    adding 'habesha_names/match/__init__.py'
    adding 'habesha_names/match/full.py'
    adding 'habesha_names/match/phonetic.py'
    adding 'habesha_names/match/token.py'
    adding 'habesha_names/parse/__init__.py'
    adding 'habesha_names/parse/compounds.py'
    adding 'habesha_names/parse/parser.py'
    adding 'habesha_names/parse/titles.py'
    adding 'habesha_names/translit/__init__.py'
    adding 'habesha_names/translit/schemes.py'
    adding 'habesha_names/translit/to_latin.py'
    adding 'habesha_names/translit/variants.py'
    adding 'habesha_names-0.1.0.dist-info/licenses/LICENSE'
    adding 'habesha_names-0.1.0.dist-info/METADATA'
    adding 'habesha_names-0.1.0.dist-info/WHEEL'
    adding 'habesha_names-0.1.0.dist-info/top_level.txt'
    adding 'habesha_names-0.1.0.dist-info/RECORD'
    removing build\bdist.win-amd64\wheel
    Successfully built habesha_names-0.1.0.tar.gz and habesha_names-0.1.0-py3-none-any.whl
    Checking dist\habesha_names-0.1.0-py3-none-any.whl: PASSED
    Checking dist\habesha_names-0.1.0.tar.gz: PASSED
    EXIT CODE: 0

Built-wheel smoke test (fresh venv in the session scratchpad, run FROM the scratchpad so the source tree is not importable):

    python -m venv smoke-venv
    smoke-venv\Scripts\pip install --quiet D:\habesha-names\dist\habesha_names-0.1.0-py3-none-any.whl
    smoke-venv\Scripts\python D:\habesha-names\scripts\smoke_wheel.py 0.1.0

Output:

    wheel smoke OK: version=0.1.0 given_names=56 match=1.00

Full repo gate (`D:\habesha-names\check.bat` = pytest -q && ruff check . && mypy src --strict, inside .venv):

    ........................................................................ [ 16%]
    ........................................................................ [ 32%]
    ........................................................................ [ 49%]
    ........................................................................ [ 65%]
    ........................................................................ [ 81%]
    .............................................x.......................... [ 98%]
    ........                                                                 [100%]
    439 passed, 1 xfailed in 3.53s
    All checks passed!
    Success: no issues found in 19 source files
    EXIT CODE: 0

Files touched: `pyproject.toml` (package-data), `src/habesha_names/__init__.py` (0.1.0), `tests/test_smoke.py` + `tests/test_public_api.py` (version pins), `CHANGELOG.md` (0.1.0 section), `MANIFEST.in` (new), `scripts/smoke_wheel.py` (new), `.github/workflows/release.yml` (new), `PROGRESS.md`

Deviations from plan (and why):
- Plan's Verify is only `python -m build && twine check dist\*`; the built-wheel smoke test was added per the Session 10 handoff requirement ("verify the lexicon loads from the built artifact, not the source tree") — it is what actually catches the package-data class of bug.
- `MANIFEST.in` and `scripts/smoke_wheel.py` are not named by the plan; both exist to make the shipped artifacts self-consistent (sdist test suite runnable; release verifiable). No engine or data changes.
- `build`/`twine` NOT added to `[project.optional-dependencies] dev` — kickoff pins dev deps to exactly pytest/ruff/mypy; installed ad hoc locally, and the release workflow installs its own copies.
- Version on `main` is now `0.1.0` (not a `.dev` marker) ahead of the actual PyPI release. Chosen so the prepared tag matches the package exactly and the workflow's tag==version gate holds; if Robel prefers dev-marking between releases, bump after tagging.

Known issues / TODOs introduced:
- The release workflow has never executed (it can only run on a tag push, which is Robel's). First real run is the integration test; the wheel-smoke gate runs before publish, so a failure cannot half-release.
- PyPI Trusted Publishing must be configured once on pypi.org BEFORE the first tag push (steps in the review-queue release item) or the publish job fails with an OIDC error — safe to just re-run after configuring.
- `PROGRESS.md` was added to `.gitignore` (commit 3a84596) but is still git-TRACKED, so the ignore entry has no effect and this file still shows in `git status`/commits. If the intent is to keep it out of the repo, it needs `git rm --cached PROGRESS.md`; flagging rather than second-guessing the intent.
- Nothing was committed, per session protocol: tree left ready for Robel. Suggested commit message: `task-10: packaging + release prep (wheel data fix, sdist manifest, v0.1.0, trusted-publishing release workflow)`.

Next session should start with: nothing — **v0.1 scope (Tasks 0–10) is complete.** The ball is in Robel's court: the Human review queue (linguistic decisions, data verification) and the release steps in the "Release tag push" item. v0.2 backlog is forbidden without explicit instruction.

## Session 12 — 2026-07-13

Task attempted: Task 11 — Alpha release prep (0.1.0a1)

What was actually done (per Robel's decision to ship an installable ALPHA now, without the native-speaker review):
- **No review-queue changes**: no `verified: false` flag flipped, no `needs_human` marker touched, queue shipped as-is. NOTE (not a queue edit): the "Release tag push" queue item's step 3 says `git tag v0.1.0` — superseded by Robel's alpha decision; the current tag is **`v0.1.0a1`** (exact commands in this session's report and below). Steps 1–2 (commit review, one-time PyPI Trusted Publisher registration) are unchanged and still pending.
- Version `0.1.0` → `0.1.0a1` (PEP 440 alpha): `src/habesha_names/__init__.py` + the two pins in `tests/test_smoke.py` / `tests/test_public_api.py`. `pyproject.toml` already carried `Development Status :: 3 - Alpha` (set in Task 0) — confirmed, no change needed.
- Honest labeling, three places: README gained an "**Alpha status**" section at the top (transliteration defaults + lexicon pending native-speaker verification; match scores and variant outputs may change in 0.1.0 final; API not frozen) and the install section now shows `pip install --pre habesha-names`; the package docstring gained a one-line version of the same disclaimer; CHANGELOG's never-published `[0.1.0]` section renamed to `[0.1.0a1] - 2026-07-13` and restructured into "Works (implemented, tested, shipped)" + "Unverified (pending native-speaker review; may change in 0.1.0 final)".
- Release mechanics confirmed by inspection, no fixes needed: `release.yml` trigger is `tags: ["v*"]`, which matches `v0.1.0a1`; the smoke gate compares `__version__` to `${GITHUB_REF_NAME#v}` by string equality, and `0.1.0a1` is already PEP 440 canonical so the built artifacts and the tag agree; Trusted Publishing block has `environment: pypi` + `id-token: write` + project URL `pypi.org/p/habesha-names`, matching remote `https://github.com/Robel231/habesha-names.git`.
- No feature, lexicon, table, or test changes beyond the version pins and labeling.

Verification output (paste FULL command + output, unedited):

Full repo gate (`D:\habesha-names\check.bat` = pytest -q && ruff check . && mypy src --strict, inside .venv):

    ........................................................................ [ 16%]
    ........................................................................ [ 32%]
    ........................................................................ [ 49%]
    ........................................................................ [ 65%]
    ........................................................................ [ 81%]
    .............................................x.......................... [ 98%]
    ........                                                                 [100%]
    439 passed, 1 xfailed in 4.33s
    All checks passed!
    Success: no issues found in 19 source files
    EXIT CODE: 0

Build + metadata check (cmd, inside .venv, dist/ removed first):

    if exist dist rmdir /s /q dist
    python -m build && twine check dist\* && echo EXIT CODE: %ERRORLEVEL%

Output (the mechanical sdist/wheel copy listings are elided for length — identical shape to Session 11's, every path now versioned `0.1.0a1`; data JSONs confirmed present in both the sdist listing and the wheel `adding` manifest; head/tail unedited):

    * Creating isolated environment: venv+pip...
    * Installing packages in isolated environment:
      - setuptools>=77
    [... sdist build: copies CHANGELOG.md, LICENSE, MANIFEST.in, README.md, pyproject.toml,
        scripts/*.py (4), src/habesha_names/** incl. data/*.json + schema.md,
        tests/test_*.py (12), tests/golden/pairs.json ...]
    * Building wheel from sdist
    [... wheel build: adding 'habesha_names/data/compounds.json',
        'habesha_names/data/given_names.json', 'habesha_names/data/schema.md',
        'habesha_names/data/titles.json' + all 24 package files ...]
    Successfully built habesha_names-0.1.0a1.tar.gz and habesha_names-0.1.0a1-py3-none-any.whl
    Checking dist\habesha_names-0.1.0a1-py3-none-any.whl: PASSED
    Checking dist\habesha_names-0.1.0a1.tar.gz: PASSED
    EXIT CODE: 0

Fresh-venv SDIST install + full test suite off the repo path (scratchpad dir `sdist-verify`, per Task 10 procedure; the sdist tarball itself installed, then unpacked and its bundled test suite run against the INSTALLED package):

    python -m venv sdist-venv
    sdist-venv\Scripts\pip install --quiet D:\habesha-names\dist\habesha_names-0.1.0a1.tar.gz pytest
    tar -xzf D:\habesha-names\dist\habesha_names-0.1.0a1.tar.gz
    sdist-venv\Scripts\python -c "import habesha_names; print('installed version:', habesha_names.__version__)"

    installed version: 0.1.0a1

    cd habesha_names-0.1.0a1
    ..\sdist-venv\Scripts\python -m pytest -q

    ........................................................................ [ 16%]
    ........................................................................ [ 32%]
    ........................................................................ [ 49%]
    ........................................................................ [ 65%]
    ........................................................................ [ 81%]
    .............................................x.......................... [ 98%]
    ........                                                                 [100%]
    439 passed, 1 xfailed in 6.70s
    EXIT CODE: 0

Installed-artifact smoke (source-tree import guard + version==tag + lexicon + engine end-to-end, same fresh venv, run from outside the repo):

    sdist-venv\Scripts\python D:\habesha-names\scripts\smoke_wheel.py 0.1.0a1

    wheel smoke OK: version=0.1.0a1 given_names=56 match=1.00
    EXIT CODE: 0

Files touched: `src/habesha_names/__init__.py` (version + docstring disclaimer), `tests/test_smoke.py` + `tests/test_public_api.py` (version pins), `README.md` (Alpha status section, `--pre` install note, "until 0.1.0 final" wording), `CHANGELOG.md` ([0.1.0a1] entry: works/unverified), `PROGRESS.md`

Deviations from plan (and why):
- Task instruction 2 says "Set classifier `Development Status :: 3 - Alpha`" — it was already present in `pyproject.toml` since Task 0; verified rather than re-added, so `pyproject.toml` is untouched this session.
- CHANGELOG's `[0.1.0] - 2026-07-13` section (cut in Session 11) was RENAMED to `[0.1.0a1]` rather than kept alongside a new entry: 0.1.0 final was never published, and a changelog entry for an unpublished version above a published alpha would be false history. 0.1.0 final gets its own entry when it actually ships.
- Committed AND pushed this session (unlike Sessions 4–11's leave-tree-ready protocol) because Robel's Task 11 instruction explicitly says "Commit as 'task-11: alpha release prep (0.1.0a1)' and push."

Known issues / TODOs introduced:
- The entire human review queue remains open by design — 0.1.0a1 ships `verified: false` data, disclosed in README/docstring/CHANGELOG. When review flips defaults, README doctests fail loudly (Session 10 design) and 0.1.0 final gets fresh verification.
- `PROGRESS.md` tracked-but-gitignored oddity from Session 11 still stands (needs `git rm --cached` if Robel wants it untracked; not second-guessed here).

Next session should start with: nothing scheduled — after Robel completes the one-time PyPI Trusted Publisher registration and pushes `v0.1.0a1` (exact commands in the Session 12 report), the release workflow runs for the first time. If it fails, that debugging is the next session.

**Post-release addendum (same day, 2026-07-13):** Robel registered the pending Trusted Publisher on pypi.org, made the repo public, and pushed `v0.1.0a1` (tag on `cf64644`). Release workflow run #1: **Success** — build 22s (incl. wheel smoke gate), publish 21s, digital attestations uploaded, no OIDC issues. Confirmed live via the PyPI JSON API (`info.version = 0.1.0a1`, `Development Status :: 3 - Alpha`, wheel 50 804 B + sdist 77 774 B) and by a real end-user install in a fresh scratchpad venv:

    pip install --pre habesha-names
    python D:\habesha-names\scripts\smoke_wheel.py 0.1.0a1

    wheel smoke OK: version=0.1.0a1 given_names=56 match=1.00

**habesha-names 0.1.0a1 is live on PyPI.** Non-blocking note for a future workflow touch-up: run #1 logged deprecation warnings that `actions/checkout@v4`, `setup-python@v5`, and the artifact actions target Node.js 20 (runners force Node 24) — bump to the @v5/@v6 majors whenever release.yml is next edited.

## Session 13 — 2026-07-14

Task attempted: task-3b — apply Robel's native-speaker review decisions (final; per-item dispositions recorded in the "Resolved 2026-07-14" block above and the Decisions log).

What was actually done:
- `translit/schemes.py`: order-8 vowel "wa"→"ua" (ሏ→lua, ሟ→mua); labialized-velar a-forms render C+"ua" (ኋ→hua, ኳ→kua, ጓ→gua, ቋ→kua; plain ዋ stays "wa"); all `verified: false` markers flipped to decided with task-3b provenance. All other consonant/vowel defaults confirmed unchanged.
- `translit/to_latin.py`: NEW word-final cluster-epenthesis rule for 6th-order runs — the epenthetic "i" goes immediately before the final coda; the coda is the last consonant, or the last two when they form the permissible cluster "st" (`_FINAL_CODAS`). Pinned: ፍቅር→Fikir, ትግስት→Tigist, ቅድስት→Kidist, ዮሐንስ→Yohanis; seeds ተስፋዬ→Tesfaye, ገብረመድህን→Gebremedhin, ጸሐይ→Tsehay, ስላሴ→Silase still hold (ገብረመድህን exercises the non-"st" coda path: d-h-i-n).
- `translit/variants.py`: added mandated rewrite rules we↔wo (0.6, Welde/Wolde/Weizero/Woizero), wa↔ua (0.5, Huala/Hwala), gn↔ny (0.5) — all key-breaking, so apply-alone; `_spelling_groups` now also serves compound prefix/second-element groups (Welde/Wolde, Selassie/Silase surface as 0.85 lexicon alternates at token level).
- Data: `titles.json` canonical Weizero/Weizerit (Woizero/Woizerit kept in abbreviation lists, W/ro etc. unchanged); `compounds.json` prefix canonical Welde (+`variants: ["Wolde"]`), W/ expansion follows (Welde 0.6/Welete 0.4), second elements gained `variants` (Maryam, Mikael, Giyorgis, Silase, Kirsitos, Igziabher, Hiiwet, Haimanot); `given_names.json` gained Mehamed/Yohanis/Danel variants; `"verified": true` on ALL entries in all three files.
- `_data.py`: `variants` field (validated: ASCII, no canonical repeats, no dups) on `CompoundPrefix`/`CompoundSecond`; shared `_latin_variants` validator; `parse/compounds.py` indexes the variant spellings (Woldemariam still splits, "Silase" recognized as second element); `data/schema.md` updated (schema keys + verified-workflow status).
- Tests: translit xfail RETIRED (round-trip now asserted at matcher level, `test_match_full.py::test_selassie_matcher_level_roundtrip`); new pins for cluster epenthesis, "ua" rendering, Welde↔Wolde ≥ 0.85 token sim, Silase↔Selassie, we↔wo/wa↔ua/gn↔ny rules, Weizero title parsing, all-entries-verified; loader fixtures updated for the new `variants` keys.
- Golden corpus: generator gained the expected `"review"` category (score strictly between the gates); the two sibling pairs moved from known_fail different-pairs to passing review-zone records; corpus regenerated.
- README: parse doctest → 'Weizero'; new "Score interpretation" (≥0.85 same / 0.60–0.85 review zone / ≤0.60 different) and "Known limitations" (Bekele↔Bikila deferred to v0.2, spaced-compound rewrite misalignment) sections; "Alpha status" and "Data verification" updated to reflect completed native-speaker review (golden corpus still needs_human).

Golden corpus before/after (regeneration required by the rule changes):

    BEFORE: total 201 | passing 195 | known_fail 6
      known_fail: same | መሐመድ <-> Mohammed | 0.5293
      known_fail: same | Gebremedhin <-> Gebrie Medhin | 0.4245
      known_fail: same | Hailemariam <-> Hailie Mariam | 0.4335
      known_fail: different | Tesfaye Girma <-> Tesfahun Girma | 0.7304
      known_fail: different | Abebe Bikila Wolde <-> Abebech Bikila Wolde | 0.8046
      known_fail: different | Bekele <-> Bikila | 0.9
    AFTER: total 204 | passing 201 | known_fail 3
      expected breakdown: same 173, different 29, review 2
      known_fail: same | Gebremedhin <-> Gebrie Medhin | 0.4245  (engine limit, README-documented)
      known_fail: same | Hailemariam <-> Hailie Mariam | 0.4335  (engine limit, README-documented)
      known_fail: different | Bekele <-> Bikila | 0.9            (deferred to v0.2 per task-3b)
      review (passing): Tesfaye Girma <-> Tesfahun Girma | 0.7304
      review (passing): Abebe Bikila Wolde <-> Abebech Bikila Wolde | 0.8046

    (መሐመድ↔Mohammed resolved by the "Mehamed" lexicon variant: now 0.85.)

D2 mechanical cross-check re-run (transliterate(fidel) vs canonical, post-cluster-rule):

    given_names: 41 OK, 14 = listed variant, 1 mismatches
      MISMATCH ኃይለማርያም Hailemaryam Hailemariam   (phonetic-key-equal; match = 0.96)
    compound seconds: 4 OK, 8 = listed variant, 0 mismatches
    compound prefixes: 9 OK, 0 = listed variant, 1 mismatches
      PREFIX MISMATCH ብርሃነ Birhane Berhane        (phonetic-key-equal; token sim = 0.91)

Verification output (paste FULL command + output, unedited):

Command: `cmd /c D:\habesha-names\check.bat` (pytest -q && ruff check . && mypy src --strict, inside .venv)

    ........................................................................ [ 16%]
    ........................................................................ [ 32%]
    ........................................................................ [ 48%]
    ........................................................................ [ 64%]
    ........................................................................ [ 80%]
    ........................................................................ [ 96%]
    ..................                                                       [100%]
    450 passed in 1.90s
    All checks passed!
    Success: no issues found in 19 source files
    GATE EXIT: 0

Pinned-output spot check (all decisions):

    OK  ፍቅር -> Fikir · ትግስት -> Tigist · ቅድስት -> Kidist · ዮሐንስ -> Yohanis
    OK  ተስፋዬ -> Tesfaye · ገብረመድህን -> Gebremedhin · ጸሐይ -> Tsehay · ስላሴ -> Silase
    OK  ኋላ -> Huala · ኳ/ጓ/ሏ/ሟ/ቋ -> Kua/Gua/Lua/Mua/Kua
    OK  sim(Welde, Wolde) = 0.85 · match(ኃይለ ሥላሴ, "Haile Selassie") = 0.91
    OK  match(መሐመድ, Mohammed) = 0.85 · parse(ወይዘሮ …).title = 'Weizero'

Files touched: `src/habesha_names/translit/schemes.py`, `src/habesha_names/translit/to_latin.py`, `src/habesha_names/translit/variants.py`, `src/habesha_names/_data.py`, `src/habesha_names/parse/compounds.py`, `src/habesha_names/parse/titles.py` (doctest), `src/habesha_names/parse/parser.py` (doctest), `src/habesha_names/data/titles.json`, `src/habesha_names/data/compounds.json`, `src/habesha_names/data/given_names.json`, `src/habesha_names/data/schema.md`, `scripts/gen_golden_pairs.py`, `tests/golden/pairs.json` (regenerated), `tests/test_translit_latin.py`, `tests/test_parse.py`, `tests/test_data_loader.py`, `tests/test_variants.py`, `tests/test_match_token.py`, `tests/test_match_full.py`, `tests/test_golden.py`, `README.md`, `review.py` (ruff fixes only), `PROGRESS.md`

Deviations from plan (and why):
- ኃይለማርያም→"Hailemaryam" and ብርሃነ→"Birhane" raw outputs were NOT added as variants: they are outside the D2 conventional-mismatch list, and both are phonetic-key-equal to their canonicals (0.96 / 0.91), so the ≥ 0.85 requirement already holds. Recorded here instead of silently extending the decided variant set.
- The compound `variants` schema field is the mechanism chosen for "keep Wolde as a recognized variant spelling" / "ሥላሴ carries Selassie and Silase": the prefix/second schemas had no variant slot, and a schema field keeps the spellings reviewable data rather than code.
- `review.py` (Robel's untracked review helper) had two ruff findings (import sort, unused import) that failed the repo gate; fixed mechanically, no behavior change.

Known issues / TODOs introduced:
- Two engine-limit known_fails remain in the corpus (spaced-compound rewrite misalignment: "Gebrie Medhin"/"Hailie Mariam") — an alignment/engine question for v0.2, not a linguistic one.
- Bekele↔Bikila 0.90 deferred to v0.2 by decision (known_fail + README "Known limitations").

Next session should start with: nothing linguistic remains open. Remaining queue: golden-corpus human curation (needs_human × 204), PyPI-name confirmation formality, and the (human-triggered) 0.1.0 final release when Robel decides.

## Decisions log

| Date | Decision | Why |
|---|---|---|
| 2026-07-10 | stdlib-only runtime, MIT, src layout | ARCHITECTURE §2 |
| 2026-07-10 | fidel tables generated, never hand-typed | Hallucination risk |
| 2026-07-10 | all agent-seeded linguistic data ships `verified: false` | Native-speaker gate |
| 2026-07-10 | no `python_version` pin in `[tool.mypy]` | mypy 2.x dropped 3.9 as a check target; CI 3.9 job covers 3.9 semantics |
| 2026-07-10 | PEP 639 license metadata (`license = "MIT"`, setuptools>=77) | Table-form `license` is deprecated/being removed in setuptools |
| 2026-07-10 | Labialized fidel = vowel order 8 within its series (`LABIALIZED_ORDER`) | Matches Unicode row layout (offset 7, -WA/-OA/-WAA names); keeps decompose/compose a clean bijection |
| 2026-07-10 | Consonant labels = lowercased Unicode name fragments + minimal override map (`TS→ts'`) | Mechanical derivation carries zero hallucination risk; overrides are flagged linguistic data |
| 2026-07-10 | `is_ethiopic` is block-range based (incl. Extended, punct, digits, marks); all-non-whitespace-chars semantics | Simple, deterministic; parser does finer-grained script detection in Task 5 |
| 2026-07-11 | Homophone collapse = series-label map applied via `str.translate` table built at import from generated tables | Mechanical derivation, zero hand-typed fidel; O(1) per char |
| 2026-07-11 | ፡ wordspace → ASCII space; other Ethiopic punct (U+1360, U+1362–U+1368) stripped; punct set derived from `unicodedata.category` | ፡ is a word separator — stripping it would merge name tokens |
| 2026-07-11 | `normalize` passes through digits/tonal/combining marks/Extended block and never raises | Task 2 scope is exactly the plan's four collapses + punct + whitespace; safety on arbitrary input |
| 2026-07-11 | `transliterate()` normalizes first, unconditionally; PRACTICAL has no rows for collapsed series | Kickoff hard requirement; homophone identity holds by construction, one source of truth |
| 2026-07-11 | PRACTICAL built at import as `_CONSONANTS` × `_VOWELS` over the generated `SYLLABLES` | No hand-typed fidel↔Latin cells; exact-coverage property test possible |
| 2026-07-11 | 6th-order ə: bare if word-final/after-vowel, else +"i"; የ glide i/y; guttural (h, glottal) order-1 "a" | Smallest context-rule set reproducing all plan round-trip seeds; all flagged for review |
| 2026-07-11 | ኃይለ ሥላሴ→"Haile Selassie" = strict xfail, no special-case | Gemination + "ie" not table-derivable; kickoff forbids silent special-casing |
| 2026-07-11 | Fidel-initial words name-cased in output; non-Ethiopic tokens byte-preserved | It's a names library; must not mangle Latin/mixed input |
| 2026-07-11 | Data files: `{"schema": 1, ...}` wrapper + exact-key validation, `LexiconError` at load | Typo safety for hand-edited linguistic data; fail loudly, never corrupt matching |
| 2026-07-11 | Loader = `@cache` lazy singleton over `importlib.resources`; the library's only stateful component | ARCHITECTURE §2; deterministic frozen dataclasses |
| 2026-07-11 | titles.json canonical Latin = plan-pinned spellings ("Woizero"), independent of the open ወ→we/wo translit default | Plan Task 4 list is the source of truth for title spellings; titles are matched by lookup, not transliteration |
| 2026-07-11 | Lexicon fidel stored as conventionally written (ፀሐይ), NFC-enforced, NOT pre-collapsed | Reviewers see real spellings; normalize() is applied by consumers at comparison time |
| 2026-07-11 | Abbreviation expansions must resolve to a known prefix or given-name canonical (cross-file check) | Catches dangling references (e.g. G/→"Girma" requires Girma in the lexicon) at load |
| 2026-07-12 | Parser matches lexicon forms after `normalize` (fidel) / lowercasing (Latin); indexes are `@cache`-built from `lexicon()` | Homophone spellings parse identically by construction; state stays in the lazy loader |
| 2026-07-12 | Comma inversion handled at tokenization, not last as §4.3 lists it | It reorders tokens for every later pipeline step; behavior unchanged |
| 2026-07-12 | `compound_confidence` = min over all compound decisions (1.0 joined / 0.9 overflow / 0.65 ambiguous / abbreviation candidate weight); `given_is_compound` scoped to the given | Deterministic, auditable; constants are review-queued heuristics |
| 2026-07-12 | Slash abbreviation expands only when letter is a known abbreviation AND remainder a known second element; top candidate applied, all candidates in the note | Explainability (AML analysts see what was chosen over what); "W/ro" can never false-positive |
| 2026-07-12 | `ParsedName.__str__` added beyond the §4.3 sketch | ARCHITECTURE §6 `parse(str(parsed))` stability property needs a canonical string form |
| 2026-07-12 | Extra tokens beyond avonym and unhandled comma patterns are noted, never silently dropped | Honesty-first parsing; downstream can audit every discarded token |
| 2026-07-12 | HabeshaKey = transliterate-first + §4.4 sketch pipeline; key format `SKELETON[A]:vowel-class`; first vowel bucketed a / e,i / o,u | Fidel and Latin spellings key identically by construction; exact first vowel breaks the plan's Mohammed=Muhammed pin |
| 2026-07-12 | Jaro-Winkler in-repo with the standard parameterization (scale 0.1, prefix cap 4, boost only above 0.7), pinned by published vectors re-derived in test comments | stdlib-only rule; textbook values make the implementation independently checkable |
| 2026-07-12 | `sim` = max(phonetic-exact 0.9, JW over transliterate+lowercase+strip); variant-overlap term deferred to Task 8 | §4.4 formula needs Task 7's `variants()`; plan explicitly allows wiring it in Task 8 |
| 2026-07-12 | Variant engine = token-level alternatives (lexicon groups, compound shapes, abbreviations) × character-level rewrites, best-first k-best enumeration, one global ranking | Deterministic top-N with `n` a pure prefix slice; explosion capped structurally, not by pruning heuristics |
| 2026-07-12 | Key-breaking rewrites (q↔k, first-vowel e→a, w↔ou, lexicon alternates, slash/dot forms) apply only in isolation; key-preserving rewrites combine up to 3 | Preserved HabeshaKey ⇒ `sim` ≥ 0.9 backstop for any combo; a lone breaking rewrite stays ≥ 0.8 by JW — together they enforce the ARCHITECTURE §6 property by construction |
| 2026-07-12 | Arabic-origin table (§4.2) = `origin: "arabic"` lexicon entries; all lexicon groups act as 0.85 whole-token alternates | No second unverified data table to review; lexicon "boosts precision" exactly as §4.5 describes |
| 2026-07-12 | `variants` property test wired against Task 6 `sim` now, slash/dot forms carved out | No import circularity in that direction; abbreviation forms need matcher-level expansion (§4.4 step 1), which is Task 8 |
| 2026-07-13 | Golden-corpus gates: same-person ≥ 0.85, different-person ≤ 0.60 | ARCHITECTURE §6 pins both; corpus tuning made the engine meet them (195/201 pairs), 6 known_fail records excepted |
| 2026-07-13 | `sim` = max(exact 1.0, phonetic 0.9, variant-overlap 0.85, JW × 0.6-if-keys-differ) | Variant term completes the §4.4 formula; the damp is the tuning that separates Tesfaye/Tesfa-style confusables (raw JW ~0.94) from real variants, which the other terms catch |
| 2026-07-13 | HabeshaKey: non-initial `y` folds to `i` (+ "aie" terminal suffix) | Corpus-driven Task 8 tuning: y writes the vowel /i/ in romanized names (Haymanot=Haimanot, Maryam=Mariam); the plan reserves key tuning for Task 8 |
| 2026-07-13 | `match` score = weighted mean over best injective role alignment × multiplicative penalties (swap 0.98, missing role `1−w·0.5`) | §4.4 swap/truncation tolerance without capping same-person truncated pairs below the 0.85 gate; constants review-queued |
| 2026-07-13 | Golden corpus is GENERATED (`scripts/gen_golden_pairs.py`, `--check` in CI) with `known_fail` markers instead of dropped failures | Same no-hand-typed-linguistic-data discipline as the fidel tables; engine limits stay visible and regressions in either direction need a conscious regeneration |
| 2026-07-13 | Memoized similarity internals (bounded `lru_cache`: norms, keys, variant sets, symmetric sim core, parsed roles) | Benchmark gate: 14.8k → 56k matches/sec; pure memoization of deterministic functions, state still only in the data loader |
| 2026-07-13 | `MatchResult` comparison dunders added beyond the §4.4 sketch (`__float__` alone) | `match(a,b) > 0.9` must "just work" per the sketch's stated intent; `__float__` alone does not enable comparisons in Python |
| 2026-07-13 | Public API = §5 surface minus v0.2 names (`to_fidel`, `guess_gender`); function exports shadow same-named subpackage attributes | Cannot export what doesn't exist; stubs violate scope discipline; shadowing is inherent to §5 naming and documented |
| 2026-07-13 | Repo-wide `mypy --strict` gate (check.bat, CI) from Task 9 onward | Kickoff engineering rule + ARCHITECTURE §6 pin CI at --strict |
| 2026-07-13 | README snippets are doctests, double-gated: plan's `python -m doctest README.md` + `test_readme_doctests` (explicit UTF-8) in pytest/CI | README claims stay executable; the pytest path is locale-independent and fails loudly when linguistic defaults change during review |
| 2026-07-13 | `__version__` bumped to `0.1.0` on main; CHANGELOG 0.1.0 section cut | Release prep: the release workflow gates tag == package version; Robel triggers by pushing `v0.1.0` |
| 2026-07-13 | `build`/`twine` installed ad hoc, never added to dev extras | Kickoff pins dev deps to pytest/ruff/mypy exactly; the release workflow installs its own build tools |
| 2026-07-13 | Wheel data via `package-data` (`data/*.json` + `schema.md`); sdist completeness via `MANIFEST.in` (tests + golden corpus + scripts + CHANGELOG) | The two artifact types have different jobs: wheel = runtime (lexicons required), sdist = rebuildable + testable (`test_golden.py` needs `pairs.json` and `gen_golden_pairs.py`) |
| 2026-07-13 | Release = tag-triggered workflow: build → twine check → install wheel in fresh venv → `scripts/smoke_wheel.py` (tag==version, lexicon loads, engine end-to-end) → PyPI Trusted Publishing (`id-token: write`, `environment: pypi`) | Plan pins human-triggered release + Trusted Publishing; the smoke gate makes the package-data bug class unshippable; no long-lived PyPI token exists anywhere |
| 2026-07-13 | Ship v0.1.0a1 ALPHA with the review queue open; `verified: false` data ships as-is, disclosed in README ("Alpha status"), package docstring, and CHANGELOG | Robel's call (Task 11): installable alpha now, native-speaker review before 0.1.0 final; PEP 440 alpha + `--pre` gate keeps it away from default `pip install` |
| 2026-07-13 | CHANGELOG `[0.1.0]` renamed to `[0.1.0a1]` (works/unverified split) instead of adding a parallel entry | 0.1.0 final never shipped; a changelog must not record an unpublished release above a published one |
| 2026-07-14 | 6th-order word-final cluster epenthesis: "i" immediately before the final coda; coda = last consonant, or last two when they form the permissible cluster "st" | Robel (task-3b): pins ፍቅር→Fikir, ትግስት→Tigist, ቅድስት→Kidist, ዮሐንስ→Yohanis without disturbing Tesfaye/Gebremedhin/Tsehay/Silase |
| 2026-07-14 | Labialized rendering "ua" not "wa": order-8 column C+"ua" (ሏ→lua), labialized-velar a-forms hua/kua/gua (ኋላ→Huala); wa↔ua added as a variant rewrite rule | Robel (task-3b): both spellings occur in the wild |
| 2026-07-14 | ወ order-1 "we" CONFIRMED → canonical Weizero/Weizerit (titles) and Welde (compound prefix); Woizero/Woizerit/Wolde kept as recognized input forms; MANDATORY we↔wo variant rule with Welde↔Wolde ≥ 0.85 pinned at token level | Robel (task-3b): Wolde/Woldemariam spellings are ubiquitous |
| 2026-07-14 | CONFIRMED as-is: ቀ→k, ቐ→q, ጸ→ts, ቸ/ጨ→ch merge, ኘ→gn (+ gn↔ny variant rule), ኸ order-1 default, የ glide, guttural order-1 "a" (kx/xw excluded), order-5 é→e, all remaining consonants, Task 1 ts' label, Task 2 order-8 collapses, ኈ/ቘ/ዀ pass-through | Robel (task-3b) native-speaker review |
| 2026-07-14 | Selassie xfail retired via lexicon: table keeps "Silase"; ሥላሴ carries Selassie/Silase variants; round-trip asserted at matcher level (match ≥ 0.85) | No silent special-casing (kickoff rule); matching is the product surface |
| 2026-07-14 | All lexicon entries (titles/compounds/given names) → "verified": true; conventional canonicals kept with raw table outputs added as variants; prefixes/second elements gained a "variants" schema field | Robel reviewed via review_report.txt; fidel↔canonical must match ≥ 0.85 |
| 2026-07-14 | Sibling-style pairs in 0.60–0.85 = INTENDED analyst-review-zone behavior: corpus "review" expectation category + README "Score interpretation" section | Robel (task-3b, E1): AML analysts should see shared-patronym near-matches |
| 2026-07-14 | Bekele↔Bikila 0.90 deferred to v0.2: stays known_fail + README "Known limitations" | Fix needs a richer phonetic-key vowel slot (task-3b, E2) |
| 2026-07-14 | ALL tuning constants (parser confidences, rewrite weights, damp, JW params, match weights) accepted for 0.1.0 as-is | Robel (task-3b, E3): revisit with a human-curated corpus |

## Known issues

_(none yet)_

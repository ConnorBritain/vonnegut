#!/usr/bin/env node
/**
 * prose-review selftest.
 *
 * Right now this covers fidelity-scan only - the deterministic sidecar the
 * fidelity critic reads. Voice-critic is tested via critic-harness.md +
 * verify-run.mjs (a different discipline: the critic is a prompt whose behaviour
 * requires spawning subagents, so it lives outside this file). Substance and
 * adversarial critics are corpus-blocked and will land here when they land.
 */

import { readdirSync, readFileSync, existsSync } from "node:fs";
import { extractAtoms, scanFidelity, verdict, renderReport } from "../tools/fidelity-scan.mjs";
import { singleWordEntityCandidates } from "./single-word-survey.mjs";
import { classifyLetter, measure, FIXTURE_LETTERS } from "./ellipsis-provenance.mjs";

let passed = 0;
let failed = 0;
const failures = [];

function check(name, condition, detail = "") {
  if (condition) {
    passed += 1;
    process.stdout.write(`  ok   ${name}\n`);
  } else {
    failed += 1;
    failures.push(`${name}${detail ? ` — ${detail}` : ""}`);
    process.stdout.write(`  FAIL ${name}${detail ? ` — ${detail}` : ""}\n`);
  }
}
function group(t) { process.stdout.write(`\n${t}\n`); }

/* ------------------------------------------------------------------ */
group("fidelity-scan — extract");

{
  const atoms = extractAtoms("The building opened in 1965 with 37 rooms.");
  const kinds = atoms.map((a) => a.kind);
  // Both numbers found - a fidelity scan that missed one of these would silently
  // pass a revision that dropped the year OR the count. The two-number sentence
  // exists in the test so a regex that stops after the first match visibly fails.
  check("both years and integers are extracted from a single sentence",
    kinds.filter((k) => k === "number").length === 2);
}

{
  const atoms = extractAtoms('Then he said "the whole plan was wrong from the start" plainly.');
  check("a >=3-word quoted span is extracted",
    atoms.some((a) => a.kind === "quote" && /whole plan was wrong/.test(a.source)));
}

{
  const atoms = extractAtoms('She said "yes" and left.');
  check("a one-word quoted emphasis is NOT extracted as a quote",
    !atoms.some((a) => a.kind === "quote"));
}

{
  const atoms = extractAtoms('He said \u201Cthe plan was wrong from the start\u201D and left.');
  check("curly-quoted spans are extracted the same as straight quotes",
    atoms.some((a) => a.kind === "quote" && /plan was wrong/.test(a.source)));
}

{
  const atoms = extractAtoms("Ahmadu Bello University was founded by Nnamdi Azikiwe.");
  const nouns = atoms.filter((a) => a.kind === "proper-noun").map((a) => a.source);
  check("multi-word proper-noun runs are extracted",
    nouns.includes("Ahmadu Bello University"));
  check("two-word named entities are extracted",
    nouns.includes("Nnamdi Azikiwe"));
}

{
  // WHAT BREAKS IF THIS REGRESSES: an entity the scan never looked at reaches
  // nobody. The run pattern used to allow ONE linking word, so "Church of the
  // Embassy" produced no atom at all - not a truncated one, since a lone
  // capitalised word is not a run. A revision could delete the church outright
  // and the report would list every atom as present, while the coverage note
  // named only the single-word gap. An undisclosed hole reads to the critic as a
  // clean check, and the critic is told the scan is authoritative on presence.
  const line = "I heard the midnight service in the Church of the Embassy.";
  const nouns = extractAtoms(line).filter((a) => a.kind === "proper-noun").map((a) => a.source);
  check("a named entity joined by two linking words is extracted",
    nouns.includes("Church of the Embassy"), nouns.join(" | "));

  const scan = scanFidelity(line, "I heard the midnight service.");
  check("and dropping it is reported as a missing atom",
    scan.missing.some((a) => a.kind === "proper-noun" && a.source === "Church of the Embassy"),
    JSON.stringify(scan.missing));
}

{
  // THE BOUND ON THE ABOVE, and it is the half that keeps an atom the size of a
  // name. Linking words chain, so an unbounded rule walks a run across a whole
  // clause; the report then names one enormous atom, and a revision that touched
  // any word inside it reads as having lost the lot. A missing-atom list that
  // misrepresents the SHAPE of a loss fails the critic the same way one that
  // omits the loss does.
  const nouns = extractAtoms("He wrote of the Battle of the Somme and of the Marne at length.")
    .filter((a) => a.kind === "proper-noun").map((a) => a.source);
  check("a linking-word chain longer than two does not extend the run",
    nouns.includes("Battle of the Somme") && nouns.every((n) => !/Somme[\s\S]*Marne/.test(n)),
    nouns.join(" | "));
}

{
  // THE BUG THIS TEST EXISTS TO PREVENT: an earlier regex used \s+ instead of
  // [ \t]+ for the inter-word gap, so a heading followed by a capitalised
  // sentence produced one huge "proper noun" like "History\n\nThe Northern".
  // That is a class of false positive that would fire on almost any structured
  // document.
  const atoms = extractAtoms("## History\n\nThe Northern Region opened it.");
  const nouns = atoms.filter((a) => a.kind === "proper-noun").map((a) => a.source);
  check("proper-noun runs do NOT span line breaks",
    nouns.every((n) => !n.includes("\n")));
  check("but the actual named entity after the heading is still caught",
    nouns.includes("The Northern Region"));
}

{
  // WHAT BREAKS IF THIS REGRESSES: every corpus file in this repo is hard-wrapped,
  // so a quote regex that stops at a newline sees only the quotes short enough to
  // fit on one line. On bacon-of-death53 that was 4 of 10 - and the tool then
  // reported the other six as neither present nor missing, which a critic reads as
  // "quotes are fine". A silent 60% coverage hole in the category the fidelity
  // critic most depends on.
  const atoms = extractAtoms('He wrote “Pompa mortis magis terret, quam\nmors ipsa.” in the margin.');
  check("a quote spanning a line break is extracted",
    atoms.some((a) => a.kind === "quote" && /Pompa mortis magis terret, quam mors ipsa\./.test(a.source)),
    JSON.stringify(atoms.filter((a) => a.kind === "quote")));
}

{
  // The bound on the above. A quotation does not contain a paragraph break; an
  // unclosed quote mark somewhere does. Without this bound one stray delimiter
  // swallows the rest of the document as a single "quote" atom, and every
  // revision then "loses" it - a tool that reports one enormous false loss per
  // typo is a tool nobody runs twice.
  const atoms = extractAtoms('He said “this one never closes\n\nA new paragraph entirely, with more words” here.');
  check("a quote does NOT run past a blank line",
    !atoms.some((a) => a.kind === "quote"),
    JSON.stringify(atoms.filter((a) => a.kind === "quote")));
}

{
  // WHAT BREAKS IF THIS REGRESSES: `[A-Z][a-z]+` silently drops any name with a
  // diacritic or ligature. "Augustus Cæsar" was not truncated and not flagged -
  // it was never an atom at all, so a revision could delete it outright and the
  // scan would report every atom present. The failure is invisible in the output,
  // which is what makes it worse than a false positive.
  const atoms = extractAtoms("Later that year Augustus Cæsar died, and Émile Zola wrote of it.");
  const nouns = atoms.filter((a) => a.kind === "proper-noun").map((a) => a.source);
  check("named entities with non-ASCII letters are extracted",
    nouns.includes("Augustus Cæsar") && nouns.includes("Émile Zola"), nouns.join(" | "));
}

{
  // WHAT BREAKS IF THIS REGRESSES: one loss is reported as two, under two
  // headings, in the list whose whole job is to show the critic the SHAPE of
  // what went. The interior of a quotation used to be scanned as prose, so
  // "Jam Tiberium" was pulled out of a Latin quotation as a named entity; a
  // revision that paraphrased the line away lost one thing and the report
  // itemised it twice. It costs the other direction too - the critic must
  // account for every flagged atom, so it spends a line clearing a name the
  // document never contained independently.
  const text = 'Tacitus saith of him, “Jam Tiberium vires et corpus, non dissimulatio, deserebant.”';
  const atoms = extractAtoms(text);
  check("a quotation's interior is not also extracted as prose",
    !atoms.some((a) => a.kind === "proper-noun"),
    JSON.stringify(atoms.filter((a) => a.kind === "proper-noun").map((a) => a.source)));
  check("but the quotation itself is still one atom",
    atoms.some((a) => a.kind === "quote" && /Jam Tiberium vires/.test(a.source)));
}

{
  // THE PAIRED NEGATIVE, and it is the reason the span is blanked to a
  // placeholder rather than to spaces. Closing the gap would let the words on
  // either side of a quotation join into a run the document never contained -
  // trading a double-report for an invented atom, which is worse: the critic is
  // forbidden to claim a flagged atom is present, so it must file a bug instead.
  const nouns = (t) => extractAtoms(t).filter((a) => a.kind === "proper-noun").map((a) => a.source);
  check("blanking a quotation does not join the prose on either side of it",
    nouns('Ahmadu "the whole plan was wrong" Bello wrote it.').length === 0,
    nouns('Ahmadu "the whole plan was wrong" Bello wrote it.').join(" | "));

  // And the bound the other way: a span too short to BE a quote atom is not
  // tracked as a quotation, so blanking it would delete coverage rather than
  // de-duplicate it. "Surly People" is a book title in the Tihonov letter and
  // the two-word quotes around it are the corpus's own typography.
  check("a quoted span too short to be a quote atom still yields its entities",
    nouns('my works are: “Surly People,” and others').includes("Surly People"),
    nouns('my works are: “Surly People,” and others').join(" | "));
}

{
  // Duplicates are collapsed. A number that appears 10 times in the original is
  // ONE atom; a revision that drops all 10 is one loss, not ten. Otherwise the
  // critic sees an inflated list and cannot tell the shape of the loss.
  const atoms = extractAtoms("The 12 rooms held 12 people, and 12 books each.");
  const twelves = atoms.filter((a) => a.kind === "number" && a.source === "12");
  check("recurring atoms are deduped", twelves.length === 1);
}

/* ------------------------------------------------------------------ */
group("fidelity-scan — presence + verdict");

{
  // A faithful revision differs in wording but preserves every material atom.
  // The verdict must be FAITHFUL - a scanner that flagged this would train
  // reviewers to ignore its output, which is the same outcome as no scanner.
  const orig = 'The 1965 report noted that "the plan was ambitious" and named Adebayo Alao.';
  const rev = 'A 1965 report described "the plan was ambitious" and cited Adebayo Alao by name.';
  const scan = scanFidelity(orig, rev);
  check("wording change with all atoms preserved is FAITHFUL",
    verdict(scan) === "FAITHFUL", `missing: ${JSON.stringify(scan.missing)}`);
}

{
  // A dropped year is a material loss. Silent acceptance of this is the exact
  // failure mode the critic exists to catch.
  const orig = "The building opened in 1965.";
  const rev = "The building opened in the mid-sixties.";
  const scan = scanFidelity(orig, rev);
  check("a dropped year triggers MATERIAL-LOSS",
    verdict(scan) === "MATERIAL-LOSS");
  check("and the missing atom is the specific year, named",
    scan.missing.some((a) => a.kind === "number" && a.source === "1965"));
}

{
  // A dropped quote counts. A paraphrase-in-place is subtle - the meaning MAY
  // survive - but the quotation as a quotation is gone, and the critic needs
  // to be told so it can decide.
  const orig = 'The chancellor said "we will finish this year" in a rare address.';
  const rev = "The chancellor promised in a rare address to finish that year.";
  const scan = scanFidelity(orig, rev);
  check("a paraphrased-out quote triggers MATERIAL-LOSS",
    verdict(scan) === "MATERIAL-LOSS");
}

{
  // A dropped named entity is a fidelity loss. Reviewers reliably miss these
  // after the reviser has run, when the pre-edit copy is gone - this is the
  // failure that most justifies the scan-first-then-critic split.
  const orig = "Ahmadu Bello University was founded in 1962.";
  const rev = "The university was founded in 1962.";
  const scan = scanFidelity(orig, rev);
  check("a dropped named entity triggers MATERIAL-LOSS",
    verdict(scan) === "MATERIAL-LOSS");
}

{
  // Numbers with thousands separators must match either form: "1,234" in the
  // original and "1234" in the revision is the same information. Anything
  // stricter would train users to write "1,234" everywhere to avoid a false
  // MATERIAL-LOSS, which teaches them to game the tool.
  const orig = "There were 1,234 attendees.";
  const rev = "There were 1234 attendees at the event.";
  const scan = scanFidelity(orig, rev);
  check("thousands separators are normalised for presence checks",
    verdict(scan) === "FAITHFUL");
}

{
  // Heading changes alone do NOT trigger MATERIAL-LOSS. A rewrite may
  // restructure legitimately. The critic sees the change and decides; the
  // verdict machine does not blow up over restructuring.
  const orig = "## Background\n\nThe library opened in 1970.";
  const rev = "## History\n\nThe library opened in 1970.";
  const scan = scanFidelity(orig, rev);
  check("a heading rename with content preserved is FAITHFUL",
    verdict(scan) === "FAITHFUL");
  // But the change is still flagged in the report - "informational, not blocking".
  check("and the heading change is still reported for review",
    scan.missing.some((a) => a.kind === "heading" && a.source === "Background"));
}

{
  // WHAT BREAKS IF THIS REGRESSES: the false-positive rate becomes a function of
  // line width. The two texts below say the same thing and differ only in where
  // the line wraps; under a literal `includes` the second reports a lost entity.
  // `n-beauty-modernised` was carried as a class-B fixture on exactly this
  // artifact, which means a scanner bug was being scored as critic behaviour.
  const orig = "It happened under Edward the Fourth of England, in 1461.";
  const rev = "It happened under Edward the\nFourth of England, in 1461.";
  const scan = scanFidelity(orig, rev);
  check("a re-wrapped named entity is present, not missing",
    verdict(scan) === "FAITHFUL", JSON.stringify(scan.missing));
}

{
  // And the paired negative: normalising whitespace must not normalise away the
  // loss itself. A presence check loose enough never to fire is the same tool as
  // no presence check, and it fails in the direction that flatters the revision.
  const scan = scanFidelity(
    "It happened under Edward the Fourth of England, in 1461.",
    "It happened under the king, in 1461.",
  );
  // ASSERTION UPDATED WITH THE LINKING-WORD FIX: the run now carries its "of
  // England" tail, so the atom is "Edward the Fourth of England". The intent is
  // unchanged and the string is strictly longer - a check that the whole entity
  // is reported gone is not a weaker check than one on its first three words.
  check("but a genuinely dropped entity is still missing after normalisation",
    scan.missing.some((a) => a.source === "Edward the Fourth of England"),
    JSON.stringify(scan.missing));
}

{
  // WHAT BREAKS IF THIS REGRESSES: the report asserts a clean result for a check
  // it never ran. The old closing line pronounced "Heading changes are
  // informational" on documents containing no headings - indistinguishable, to
  // the critic reading it, from a heading check that ran and found nothing. Two
  // critics caught it independently; nothing in this suite did.
  const noHeadings = renderReport(scanFidelity("The report ran in 1965.", "The report ran in 1965."));
  check("a pair with no headings makes no claim about headings",
    /original has none/.test(noHeadings) && !/Heading changes are informational/.test(noHeadings),
    noHeadings);

  const withHeadings = renderReport(scanFidelity(
    "## Background\n\nThe report ran in 1965.", "## Background\n\nThe report ran in 1965."));
  check("a pair WITH headings says how many were checked",
    /headings: 1 checked/.test(withHeadings), withHeadings);
}

{
  // The report must name what it cannot see. A FAITHFUL verdict over atoms that
  // exclude single-word names, word-form numbers and every hedge is a statement
  // about a list, not about the revision - and the critic downstream is told the
  // scan is authoritative on presence, so an unqualified "none missing" is the
  // one sentence most likely to be over-read.
  for (const [label, r] of [
    ["FAITHFUL", renderReport(scanFidelity("Ran in 1965.", "Ran in 1965."))],
    ["MATERIAL-LOSS", renderReport(scanFidelity("Ran in 1965.", "Ran some time ago."))],
  ]) {
    check(`the ${label} report names the categories it never examined`,
      /NOT extracted, on any pair: single-word named entities/.test(r), r);

    // FOUND BY A CRITIC, ON THE RUN THAT FIRST SAW THE COVERAGE NOTE. The first
    // wording illustrated the gap with "Suvorin, Salon" - real entities from one
    // fixture. A critic reading them in a document containing neither filed a
    // scanner defect: an example that looks like an observation about this pair
    // is one, to the only reader the report has. WHAT BREAKS IF THIS REGRESSES:
    // the block written to stop the tool over-claiming starts making claims of
    // its own about text it never saw.
    check(`the ${label} report's coverage examples name no corpus entity`,
      !/Suvorin|Salon|Levitan|Fourmis|Cæsar|Sahalin/.test(r) && /CATEGORIES, not observations/.test(r), r);
  }
}

{
  // THE EVIDENCE FOR A DELIBERATE GAP, checked in so it can be overturned with
  // measurements rather than argued with in a comment. P3(c) asked whether
  // single-word entities should be extracted. They are not, and the reason is
  // that the candidate list is roughly half ordinary capitalised English while
  // the critic is told the scan is AUTHORITATIVE on presence.
  //
  // WHAT BREAKS IF THIS REGRESSES: the docstring's numbers stop matching the
  // code and the decision reverts to folklore - which is the failure mode
  // CALIBRATION.md is a list of.
  const dir = new URL("fixtures/fidelity/", import.meta.url);
  const names = readdirSync(dir, { withFileTypes: true }).filter((e) => e.isDirectory()).map((e) => e.name);
  const candidates = new Set();
  const insideAQuote = new Set();
  for (const n of names) {
    const text = readFileSync(new URL(`${n}/original.md`, dir), "utf8");
    const quoted = extractAtoms(text).filter((a) => a.kind === "quote").map((a) => a.source).join(" ");
    for (const w of singleWordEntityCandidates(text)) {
      candidates.add(w);
      if (new RegExp(`\\b${w}\\b`, "u").test(quoted)) insideAQuote.add(w);
    }
  }

  // Not named entities in any reading - ordinary capitalised English, demonyms,
  // weekdays, months, and Latin words sitting inside quotations. This list is the
  // judgement; everything else in this block is mechanical.
  //
  // RE-MEASURED AFTER THE LINKING-WORD AND QUOTE-INTERIOR FIXES, because this
  // whole block is derived from what the TOOL extracts and both fixes moved
  // that. "Russian" and "Serbs" left the candidate list - the longer run
  // pattern now swallows them into "One of the Russian" and "The Czechs and the
  // Serbs" - and "Jam", "Tiberium" and "Twilight" joined it, because they used
  // to be covered by proper-noun runs the tool no longer extracts from inside
  // quotations. Net 55 -> 53. The numbers are updated to what the code now does;
  // tuning the code to preserve them would be the tail wagging the dog.
  const notEntities = ["Adeste", "April", "Auto", "Cogita", "Deus", "Easter", "Exhibition",
    "Extinctus", "Faculties", "February", "Feri", "French", "Frenchmen", "Germans", "Jam",
    "January", "Nunc", "October", "Pompa", "Pulchrorum", "Romani", "Saturday",
    "Stoics", "Stories", "Thursday", "Ut"];
  check("the single-word-entity survey still yields 53 candidates over the fixture originals",
    candidates.size === 53, `got ${candidates.size}`);
  check("every word the survey calls a non-entity is still produced by the rule",
    notEntities.every((w) => candidates.has(w)),
    notEntities.filter((w) => !candidates.has(w)).join(" "));
  check("so the rule remains roughly half ordinary capitalised English",
    notEntities.length / candidates.size > 0.4,
    `${notEntities.length} of ${candidates.size}`);
  // 10 -> 13 for a reason that STRENGTHENS the argument this block records: the
  // tool stopped extracting prose atoms from inside quotations, so three words
  // it used to double-report as part of a run now show up here instead - still
  // duplicating a loss the quote atom already carries. The permissive
  // single-word rule would re-introduce exactly the duplication the
  // quote-interior fix removed.
  check("and 13 candidates duplicate a loss the quote atoms already report",
    insideAQuote.size === 13, `got ${insideAQuote.size}: ${[...insideAQuote].sort().join(" ")}`);

  // The counterweight, and it is why this is a survey rather than a one-line
  // won't-fix: the rule DOES find the entities the harness transcripts said the
  // scanner missed. Anyone re-opening this decision should start here.
  check("the rule would nonetheless have caught the entities the run reported missing",
    ["Suvorin", "Levitan", "Fourmis", "Salon"].every((w) => candidates.has(w)));
}

{
  // The rendered report exists to be read by the critic prompt. If either
  // classification section vanishes silently, the critic loses a signal.
  const scan = scanFidelity(
    "Ahmadu Bello University opened in 1962.",
    "The university opened years ago.",
  );
  const r = renderReport(scan);
  // ASSERTION REPLACED: this used to require the literal `fidelity: MATERIAL-LOSS`
  // headline, and that headline is the defect fixed below. What it was there to
  // guarantee - the reader can tell at a glance which way the check came out -
  // is asserted here in the wording the report now uses.
  check("the report states its result on the first line",
    /presence check: material atoms missing/.test(r), r);
  check("and lists each kind of missing atom under its own header",
    /numbers absent from the revision:/.test(r) && /named entities absent from the revision:/.test(r));
  check("the report says the critic decides which losses matter",
    /critic that/.test(r));
}

{
  // WHAT BREAKS IF THIS REGRESSES: the first line of the critic's input answers
  // the question the critic was convened to decide. The report opened
  // `fidelity: FAITHFUL` - the exact word the critic must end its own review
  // with - over a check that only compared strings. Claim drift, a dropped
  // qualification and a reversed polarity leave every word on the page, so the
  // tool cannot see the losses a competent rewrite actually produces, and the
  // coverage note at the bottom cannot undo the word at the top. Two critics on
  // the S4 run said so independently. `verdict()` keeps the two words for
  // callers who know what they are; the rendered text does not get them.
  for (const [label, r] of [
    ["clean", renderReport(scanFidelity("Ran in 1965.", "Ran in 1965."))],
    ["lossy", renderReport(scanFidelity("Ran in 1965.", "Ran some time ago."))],
  ]) {
    check(`the ${label} report does not print the critic's verdict vocabulary`,
      !/FAITHFUL|MATERIAL-LOSS/.test(r), r);
    check(`the ${label} report's headline names the check it actually ran`,
      /^\s*presence check: /m.test(r), r);
    check(`the ${label} report disclaims being a fidelity verdict`,
      /Not a fidelity verdict\./.test(r), r);
  }

  // And the half that keeps the disclaimer from being decoration: a clean result
  // must say what it is a statement ABOUT. "None missing" over a list that
  // excludes every phrasing-carried fact is the sentence most likely to be
  // over-read by a critic told the scan is authoritative on presence.
  const clean = renderReport(scanFidelity("Ran in 1965.", "Ran in 1965."));
  check("a clean result says it is a statement about the atoms, not the revision",
    /not a statement about the revision/i.test(clean), clean);
}

/* ------------------------------------------------------------------ */
group("fidelity fixtures — integrity");

{
  const dir = new URL("fixtures/fidelity/", import.meta.url);
  const manifest = JSON.parse(readFileSync(new URL("fixtures.json", dir), "utf8"));
  const corpus = new URL(`${manifest.corpus_root}/`, dir);
  const onDisk = readdirSync(dir, { withFileTypes: true })
    .filter((e) => e.isDirectory())
    .map((e) => e.name)
    .sort();
  const declared = manifest.fixtures.map((f) => f.name).sort();

  // A fixture on disk but not in the manifest is a fixture whose expected verdict
  // nobody wrote down, and it would be silently absent from the harness denominator -
  // the direction that flatters a result. Same corpus discipline as prose-tell-scan.
  check("every fixture directory is declared in fixtures.json",
    JSON.stringify(onDisk) === JSON.stringify(declared),
    `disk=${onDisk.length} manifest=${declared.length}`);

  for (const f of manifest.fixtures) {
    const original = readFileSync(new URL(`${f.name}/original.md`, dir), "utf8");

    // THE ANTI-TUNING CHECK. If I can edit an "original", I can edit it until a
    // fixture produces the verdict I wanted, and the harness measures nothing. The
    // original is the corpus file or it is not evidence.
    // A fixture may override corpus_root. The reviser set was single-root (Gutenberg
    // essays) until FU-3 broadened it, and a modern voice does not live in that tree —
    // so the alternative to an override was leaving the corpus period-locked, which is
    // the limitation FU-3 exists to remove.
    const root = f.corpus_root ? new URL(`${f.corpus_root}/`, dir) : corpus;
    const source = readFileSync(new URL(f.source, root), "utf8");
    check(`${f.name}: original is byte-identical to ${f.source}`, original === source);

    // THE LEAK GUARD, and it exists because the first harness run was invalid.
    // Every revision.md carried `expect: FAITHFUL` in its frontmatter - the answer,
    // sitting in a file the critic is required to read. Six transcripts had to be
    // thrown away. A subagent noticed and said so; nothing in the repo would have.
    // The expected verdict lives in fixtures.json, which the harness forbids reading,
    // and it may live nowhere else.
    for (const file of ["original.md", "revision.md"]) {
      const text = readFileSync(new URL(`${f.name}/${file}`, dir), "utf8");
      const fm = text.match(/^---\n([\s\S]*?)\n---\n/);
      check(`${f.name}/${file}: frontmatter does not leak the expected verdict`,
        !fm || !/FAITHFUL|MATERIAL-LOSS|\bexpect\b/.test(fm[1]),
        fm ? fm[1].replace(/\n/g, " ") : "");

      // A revision whose `fixture:` names a directory it is not in is either a
      // copy-paste error or an undocumented rename. One fixture here legitimately
      // carries its old name - that stale name is the provenance proving its
      // transcript predates the rename - so the manifest has to declare it.
      const declared = fm && fm[1].match(/^fixture:\s*(\S+)/m);
      if (declared) {
        check(`${f.name}/${file}: frontmatter names this fixture, or its declared former name`,
          declared[1] === f.name || declared[1] === f.previously_named,
          `says ${declared[1]}`);
      }
    }

    // The recorded scan verdict is what makes "an echo of the scanner scores 6/12"
    // a re-derived number instead of a sentence in a README. If a revision is edited
    // and its class silently shifts, the published baseline is wrong and this fails.
    const scan = scanFidelity(original, readFileSync(new URL(`${f.name}/revision.md`, dir), "utf8"));
    check(`${f.name}: fidelity-scan still returns ${f.scan_verdict}`,
      verdict(scan) === f.scan_verdict, `got ${verdict(scan)}`);

    // Class is the (scan, expected-critic) pair. Stating it in prose AND in the two
    // fields lets them drift apart; this makes the prose accountable to the fields.
    const expectedClass = { "FAITHFUL|FAITHFUL": "A", "MATERIAL-LOSS|FAITHFUL": "B",
      "MATERIAL-LOSS|MATERIAL-LOSS": "C", "FAITHFUL|MATERIAL-LOSS": "D" }[`${f.scan_verdict}|${f.expect}`];
    check(`${f.name}: declared class ${f.class} matches its scan/expect pair`,
      f.class === expectedClass, `pair implies ${expectedClass}`);

    // negative = must come back FAITHFUL, positive = must come back MATERIAL-LOSS.
    // verify-run.mjs derives the two denominators from the filename prefix, so a
    // disagreement here would move a result between them with nothing to notice.
    const impliedKind = f.expect === "FAITHFUL" ? "negative" : "positive";
    check(`${f.name}: kind, filename prefix and expected verdict agree`,
      f.kind === impliedKind && f.name.startsWith(f.kind === "positive" ? "p-" : "n-"));
  }

  // Both disagreement directions must be represented, or the harness cannot show the
  // critic is anything other than a wrapper around the regex. B = scanner over-flags,
  // D = scanner is blind. Losing either class silently guts the acceptance argument.
  const byClass = (c) => manifest.fixtures.filter((f) => f.class === c).length;
  process.stdout.write(`  ---- class distribution: ${["A", "B", "C", "D"].map((c) => `${c}=${byClass(c)}`).join(" ")}\n`);

  // MINIMUM TWO, not one, and the reason is a near miss. Class B started at three;
  // reclassifying p-death-severus-unnamed dropped it to two, and the only reason
  // anyone noticed was a reviewer reading the diff - a "> 0" guard sat there green
  // while the class the harness calls load-bearing quietly halved. A class carried
  // by a single fixture is carried by that fixture's arguable edges, not by the
  // property it is supposed to demonstrate.
  //
  // TWO IS A DEFAULT, NOT A MEASUREMENT. Nothing derived it; it is the smallest
  // number that is not one. Raise it when there is a reason to, and say so.
  for (const c of ["B", "D"]) {
    const what = c === "B" ? "scanner over-flags, critic clears" : "scanner blind, critic catches";
    check(`class ${c} (${what}) has at least 2 fixtures`, byClass(c) >= 2, `has ${byClass(c)}`);
  }
}

/* ------------------------------------------------------------------ */
group("structure fixtures — integrity");

{
  const { STRUCTURE_FIXTURES, ECHO_RULE, scanSays, scanDraft, loadStructureManifest, structureFixtures } = await import("./structure-harness.mjs");
  const { pathToFileURL } = await import("node:url");
  const { join } = await import("node:path");
  const manifest = loadStructureManifest();
  const onDisk = readdirSync(STRUCTURE_FIXTURES, { withFileTypes: true }).filter((e) => e.isDirectory()).map((e) => e.name).sort();
  const declared = manifest.fixtures.map((f) => f.name).sort();
  check("every structure fixture directory is declared in fixtures.json", JSON.stringify(onDisk) === JSON.stringify(declared), `disk=${onDisk.length} manifest=${declared.length}`);
  check("fixtures.json states the echo rule it was classified under, and it is the harness's", manifest.echo_rule === ECHO_RULE.description);
  const outlineSchemaPath = join(STRUCTURE_FIXTURES, "..", "..", "..", "..", "prose-outline", "skills", "prose-outline", "tools", "lib", "outline-schema.mjs");
  const outlineSchema = existsSync(outlineSchemaPath) ? await import(pathToFileURL(outlineSchemaPath).href) : null;
  for (const f of manifest.fixtures) {
    const draft = readFileSync(join(STRUCTURE_FIXTURES, f.name, "draft.md"), "utf8");
    const outlinePath = join(STRUCTURE_FIXTURES, f.name, "outline.json");
    const hasOutline = existsSync(outlinePath);
    // THE LEAK GUARD. The critic reads draft.md and outline.json; the answer may live in
    // fixtures.json and nowhere else. The verdict words, expectation keys and class
    // letters are what leaked once before, in a file a critic must read.
    for (const [file, text] of [["draft.md", draft], ...(hasOutline ? [["outline.json", readFileSync(outlinePath, "utf8")]] : [])]) {
      check(`${f.name}/${file}: carries no verdict word, expectation key or class label`,
        !/\b(?:CLEAN|REVISE)\b/.test(text) && !/^\s*(?:expect|class|verdict|scan_says)\s*:/im.test(text));
    }
    check(`${f.name}: mode matches whether an outline is staged`, (f.mode === "intended-outline") === hasOutline);
    if (hasOutline && outlineSchema) {
      check(`${f.name}/outline.json validates as a voice-outline/1 body`, outlineSchema.validateOutlineBody(JSON.parse(readFileSync(outlinePath, "utf8"))).length === 0);
    }
    // The recorded echo verdict is re-derived from the draft, so an edited draft whose
    // class silently shifts fails here rather than in a published baseline.
    const says = scanSays(await scanDraft(draft));
    check(`${f.name}: the echo rule still says ${f.scan_says}`, says === f.scan_says, `got ${says}`);
    const expectedClass = { "CLEAN|CLEAN": "A", "REVISE|CLEAN": "B", "REVISE|REVISE": "C", "CLEAN|REVISE": "D" }[`${f.scan_says}|${f.expect}`];
    check(`${f.name}: declared class ${f.class} matches its echo/expect pair`, f.class === expectedClass, `pair implies ${expectedClass}`);
    const impliedKind = f.expect === "CLEAN" ? "negative" : "positive";
    check(`${f.name}: kind, filename prefix and expected verdict agree`, f.kind === impliedKind && f.name.startsWith(f.kind === "positive" ? "p-" : "n-"));
  }
  const byClass = (c) => manifest.fixtures.filter((f) => f.class === c).length;
  process.stdout.write(`  ---- class distribution: ${["A", "B", "C", "D"].map((c) => `${c}=${byClass(c)}`).join(" ")}\n`);
  for (const c of ["A", "B", "C", "D"]) {
    check(`structure class ${c} has at least 2 fixtures`, byClass(c) >= 2, `has ${byClass(c)}`);
  }
  // The leave-one-out set is named, not globbed: twelve corpus essays that exist and
  // are argumentative human prose. Every one reads REVISE under the echo rule, which is
  // the point — the parrot flags every human essay, so the critic must beat 0 of 12.
  const loo = structureFixtures().filter((x) => x.name.startsWith("n-loo-"));
  check("twelve named leave-one-out essays, all present in the corpus", loo.length === 12 && loo.every((x) => existsSync(x.inputs[0].from)));
  let parrotFlags = 0;
  for (const x of loo) if (scanSays(await scanDraft(readFileSync(x.inputs[0].from, "utf8"))) === "REVISE") parrotFlags += 1;
  check(`the echo rule flags every leave-one-out essay (parrot baseline 0 of 12), as fixtures.json says (${parrotFlags} of 12)`, parrotFlags === 12);
}

/* ------------------------------------------------------------------ */
group("primitive/bundle parity");

{
  // AGENTS.md rule 1: the rendered agent's body must be byte-identical to the
  // primitive's, and "there's no generator yet, so this is maintained by hand."
  // A drifted pair silently ships two different agents under one name, which is
  // exactly the class of failure nobody notices by reading. Hand-maintained and
  // unchecked is the combination CALIBRATION.md is a list of.
  const body = (url) => readFileSync(url, "utf8").split(/^---$/m).slice(2).join("---");
  for (const name of ["prose-voice-critic", "prose-fidelity-critic"]) {
    const primitive = new URL(`../../../primitives/agents/${name}/agent.md`, import.meta.url);
    const rendered = new URL(`../agents/${name}.md`, import.meta.url);
    check(`${name}: rendered body is byte-identical to the primitive`,
      body(primitive) === body(rendered));

    // Frontmatter may add tools/model/color from meta.yaml and nothing else. A
    // description that drifts is a dispatcher reading one thing and a reader another.
    const fm = (url) => Object.fromEntries(readFileSync(url, "utf8").split(/^---$/m)[1]
      .split("\n").filter((l) => l.includes(":"))
      .map((l) => [l.slice(0, l.indexOf(":")).trim(), l.slice(l.indexOf(":") + 1).trim()]));
    const [p, r] = [fm(primitive), fm(rendered)];
    check(`${name}: primitive frontmatter carries only name + description`,
      JSON.stringify(Object.keys(p).sort()) === JSON.stringify(["description", "name"]));
    check(`${name}: rendered name and description match the primitive`,
      p.name === r.name && p.description === r.description);
    check(`${name}: rendered frontmatter adds only tools/model/color`,
      Object.keys(r).every((k) => ["name", "description", "tools", "model", "color"].includes(k)),
      Object.keys(r).join(","));
  }
}

/* ------------------------------------------------------------------ */
group("reviser fixtures — integrity");

{
  const dir = new URL("fixtures/reviser/", import.meta.url);
  const manifest = JSON.parse(readFileSync(new URL("fixtures.json", dir), "utf8"));
  const corpus = new URL(`${manifest.corpus_root}/`, dir);
  const onDisk = readdirSync(dir, { withFileTypes: true })
    .filter((e) => e.isDirectory())
    .map((e) => e.name).sort();
  const declared = manifest.fixtures.map((f) => f.name).sort();

  // Same anti-tuning rule as the fidelity fixtures: a fixture I can invent by hand is a
  // fixture I can tune until the acceptance run passes. A fixture whose original is a
  // corpus file I did not write cannot be tuned that way. The plan is authored, and its
  // quotes are checked against the (immutable) original — a bogus quote produces a REFUSE
  // rather than a bad edit, which is intended for exactly one fixture and would be a real
  // authoring defect on any other.
  check("every reviser fixture directory is declared in fixtures.json",
    JSON.stringify(onDisk) === JSON.stringify(declared), `disk=${onDisk.length} manifest=${declared.length}`);

  const STRIP = (t) => { const m = t.match(/^---\n[\s\S]*?\n---\n/); return m ? t.slice(m[0].length) : t; };
  for (const f of manifest.fixtures) {
    const orig = readFileSync(new URL(`${f.name}/original.md`, dir), "utf8");
    // A fixture may override corpus_root. The reviser set was single-root (Gutenberg
    // essays) until FU-3 broadened it, and a modern voice does not live in that tree —
    // so the alternative to an override was leaving the corpus period-locked, which is
    // the limitation FU-3 exists to remove.
    const root = f.corpus_root ? new URL(`${f.corpus_root}/`, dir) : corpus;
    const source = readFileSync(new URL(f.source, root), "utf8");
    check(`${f.name}: original is byte-identical to ${f.source}`, orig === source);

    const plan = JSON.parse(readFileSync(new URL(`${f.name}/plan.json`, dir), "utf8"));
    check(`${f.name}: plan declares mode plan-only (default)`, plan.mode === "plan-only",
      `mode=${JSON.stringify(plan.mode)}`);
    check(`${f.name}: plan has at least one entry`, Array.isArray(plan.entries) && plan.entries.length >= 1);

    // Every plan entry's quote MUST appear verbatim in the original body, EXCEPT for
    // fixtures whose whole point is refusing on a drifted quote. That exception is stated
    // per-fixture rather than inferred from the name.
    const body = STRIP(orig);
    const mustDrift = f.kind === "refuse-quote-drift";
    for (const e of plan.entries) {
      const found = body.includes(e.location.quote);
      check(`${f.name}/${e.id}: quote ${mustDrift ? "must NOT match (refuse test)" : "matches original verbatim"}`,
        mustDrift ? !found : found);
    }

    // The leak guard: same discipline as the fidelity fixtures. A plan entry that
    // mentions the expected verdict is a plan that tells the reviser what to do AND what
    // it will be judged as, which contaminates the measurement. The plan reasons live
    // inside `reason` fields; those may name a critic, but they may not name a verdict.
    const planText = JSON.stringify(plan);
    check(`${f.name}: plan does not leak a fidelity verdict (FAITHFUL/MATERIAL-LOSS)`,
      !/(FAITHFUL|MATERIAL-LOSS)/i.test(planText.replace(/"[a-z_]+":"/g, "")));

    // The manifest's `expected` block is metadata for the harness runner and the
    // acceptance run, not something the reviser sees. Explicitly asserted here so a
    // future harness change that started passing `expected` to the primitive would fail.
    check(`${f.name}: manifest declares expected gate + reviser outcome`,
      typeof f.expected?.gate === "string" && typeof f.expected?.reviser === "string");
  }

  // Class-coverage guard. If someone deletes the refuse-tests, the ship bar becomes
  // "the reviser was well-behaved on the easy cases", which is not what the ship bar
  // measures. Same shape as the fidelity fixtures' class B / D requirement.
  const kinds = new Set(manifest.fixtures.map((f) => f.kind));
  for (const required of ["faithful-local-edit", "refuse-quote-drift", "refuse-ambiguous", "gate-catches-loss"]) {
    check(`reviser fixtures cover the '${required}' kind`, kinds.has(required));
  }
}

/* ------------------------------------------------------------------ */
group("prose-reviser primitive — parity guard");

// AGENTS.md rule 1: primitives/ is the source, bundles/ is the deployment.
// A held primitive (ships: false) must NOT be rendered — no absent-copy drift.
// A shipped primitive (ships: true) MUST be rendered with a body byte-identical
// to the primitive's agent.md (frontmatter may differ to add tools/model/color).
{
  const primitiveDir = new URL("../../../primitives/agents/prose-reviser/", import.meta.url);
  const meta = readFileSync(new URL("meta.yaml", primitiveDir), "utf8");
  const held = /^ships:\s*false\b/m.test(meta);
  const shipped = /^ships:\s*true\b/m.test(meta);
  const renderedURL = new URL("../agents/prose-reviser.md", import.meta.url);
  const renderedExists = existsSync(renderedURL);

  // Exactly one of held/shipped must be true.
  check("prose-reviser: meta.yaml declares ships as exactly one of true or false",
    held !== shipped);

  // Held → absent from bundle, and a reason is on record.
  check("prose-reviser: a held primitive is absent from the bundle's agents/ directory",
    !held || !renderedExists);
  check("prose-reviser: a held primitive declares a held_reason",
    !held || /^held_reason:\s*\S/m.test(meta));

  // Shipped → rendered under bundle, body byte-identical to the primitive's agent.md.
  if (shipped) {
    check("prose-reviser: a shipped primitive is rendered into the bundle's agents/",
      renderedExists);
    if (renderedExists) {
      const stripFrontmatter = (s) => s.replace(/^---\n[\s\S]*?\n---\n/, "");
      const src = stripFrontmatter(readFileSync(new URL("agent.md", primitiveDir), "utf8"));
      const dst = stripFrontmatter(readFileSync(renderedURL, "utf8"));
      check("prose-reviser: rendered body is byte-identical to primitives/ source (AGENTS.md rule 1)",
        src === dst);
    }
  }
}

group("ellipsis provenance — the classifier FU-6's finding rests on");
{
  // FU-6 withdrew one of S1's four Chekhov findings on the strength of this
  // classifier: 47.4% of the corpus's ellipses sit at a paragraph or letter
  // boundary and therefore cannot be an authorial pause. If the position logic is
  // wrong, a published correction is wrong, and nothing else in the repo would
  // notice — the script prints plausible percentages either way.
  const one = (text) => classifyLetter(text).hits.map((h) => h.cls);

  check("an ellipsis opening the first paragraph is a cut before the letter starts",
    one("... and so I left.\n\nA second paragraph.")[0] === "opens-letter");

  check("an ellipsis opening a later paragraph is a cut, not a pause",
    one("First paragraph here.\n\n... resuming mid-flow now.")[0] === "opens-paragraph");

  check("an ellipsis closing the last paragraph is a cut after the letter ends",
    one("First paragraph here.\n\nThe sentence trails off....")[0] === "closes-letter");

  check("an ellipsis closing a middle paragraph is a truncation",
    one("Truncated here....\n\nA later paragraph.")[0] === "closes-paragraph");

  // The one class that cannot be an excision: there is no removable unit between
  // two lowercase words. This is the "Rain, cold, mud ... brrr!" case, and it is
  // the entire surviving authorial habit.
  check("lowercase either side is scored as the author, not the editor",
    one("I had to wait. Rain, cold, mud ... brrr! The line is good.")[0] === "mid-sentence");

  // The honest bucket. Scoring these as authorial would have inflated the
  // surviving rate more than tenfold and reversed the finding.
  check("a capital after the ellipsis is undecidable, not credited to the author",
    one("There is nothing.... There is a General, though.")[0] === "between-sentences");

  check("both three- and four-dot forms are counted",
    classifyLetter("Mid ... pause and mid .... pause here.").hits.length === 2);

  check("frontmatter is stripped before positions are read",
    one("---\nsource: x\n---\n... opening cut.\n\nSecond.")[0] === "opens-letter");

  // The published numbers must be reproducible from the corpus on demand, not
  // trusted from a doc someone typed.
  const m = measure(FIXTURE_LETTERS);
  check("the 10 S2 fixture letters still measure as FU-6 published them",
    m.total === 46 && m.boundary === 22 && m.authorial === 4 && m.indeterminate === 20,
    `total ${m.total}, boundary ${m.boundary}, authorial ${m.authorial}, undecidable ${m.indeterminate}`);
  check("the defensible authorial rate is still far below the naive reading",
    (m.authorial * 1000) / m.words < 1 && (m.total * 1000) / m.words > 5);
}

process.stdout.write(`\n${"─".repeat(60)}\n`);
process.stdout.write(`${passed} passed, ${failed} failed\n`);
if (failed) {
  process.stdout.write(`\nFailures:\n${failures.map((f) => `  - ${f}`).join("\n")}\n`);
}
process.exit(failed ? 1 : 0);

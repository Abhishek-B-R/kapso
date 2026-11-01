# Verification

Check the attempt for leakage and for an honest validation. The verdict is
valid or void, with evidence; an unresolved check is named, never passed.

1. When the data is a relational benchmark database, run the leakage-scan
   skill's script over the whole candidate (tree mode) with the regime the
   domain statement names (the temporal-protocol skill's three): it reports
   reads outside the sanitized copy and
   the task's data, the test table unmasked or its removed columns read, a
   cache location overridden, a reach outside a per-tick snapshot, a load
   that truncates under per-row seed time, and the advisory sites where
   training and validation rows mix. On any other data shape the script
   says nothing about the split: step 2 is the gate.
2. Ask the leakage-auditor with the diff, the inherited code and the
   evaluation output. It establishes the data flow itself: features from
   rows after the row's own time, folds that split a repeated unit, labels
   in features, the evaluation data used to train, a transform fitted
   before the split, augmentation before the split, validation labels in
   the chain that produces validation predictions.
3. Read the evaluation output against the task's history: convert a
   published bar to the metric's own units before comparing; a validation
   score far above the published entries, a windowed reading that collapses
   while the flat one holds, a per-tick history that stops growing at a
   fixed date, or a public measurement far below the internal one is
   evidence to investigate, not a verdict by itself.
4. A sentence in the attempt notes saying a finding is safe is evidence to
   assess, not a pass: check it against the data flow. Void when a
   prohibited flow stands or a reported score is not the evaluation's;
   otherwise valid, with a summary naming what was checked, what was found
   safe, and what could not be checked.

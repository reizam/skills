# Sources

The evidence behind `prune`'s rules, for a human questioning one. A run never
needs this file.

| Rule | Evidence |
|---|---|
| Redundancy by red sets, never by coverage | Shi, Gyori, Gligoric, Zaytsev, Marinov — *Balancing trade-offs in test-suite reduction*, FSE 2014: reducing by statement coverage cut 62.9 % of tests and lost up to 20.5 % of killed mutants; reducing by killed mutants lost none, for suites 11.9 points larger. [PDF](https://mir.cs.illinois.edu/awshi2/publications/FSE2014.pdf) |
| A break caught only by this test is a real promise | Petrović, Ivanković et al. — *Does mutation testing improve testing practices?*, ICSE 2021: mutants coupled with 70 % of 1 502 high-priority real bugs. [arXiv](https://arxiv.org/abs/2103.07189) |
| Leave arid code alone; a promise only an arid break reveals is a change-detector | Petrović, Ivanković, Fraser, Just — *Practical Mutation Testing at Scale*, TSE 2021: 85 % of raw mutants judged unproductive, 89 % productive after arid-node suppression. [arXiv](https://arxiv.org/abs/2102.11378) · Google Testing on the Toilet, *Change-Detector Tests Considered Harmful*, 2015. [post](https://testing.googleblog.com/2015/01/testing-on-toilet-change-detector-tests.html) |
| Extreme breaks first | Vera-Pérez, Monperrus, Baudry et al. — pseudo-tested methods, EMSE 2018: 1–46 % of covered methods survive having their body removed; one mutant per method. [arXiv](https://arxiv.org/abs/1807.05030) · Niedermayr, Juergens, Wagner 2016: 6–53 %. [arXiv](https://arxiv.org/abs/1611.07163) |
| Check a silent break for equivalence | Foster et al. (Meta) — *Mutation-Guided LLM-based Test Generation*, FSE 2025: an equivalence judge at 0.95 precision / 0.96 recall with preprocessing. [arXiv](https://arxiv.org/abs/2501.12862) |
| Never-failed is a prior, not a proof | Memon et al. — Google TAP, ICSE-SEIP 2017: 97.93 % of test targets never failed. [PDF](https://research.google.com/pubs/archive/45861.pdf) |
| Flakiness as a rate, per layer, on the default branch | Meta, *Probabilistic flakiness*, 2020. [post](https://engineering.fb.com/2020/12/10/developer-tools/probabilistic-flakiness/) · Trunk flaky-test detection by branch. [docs](https://docs.trunk.io/flaky-tests/detection) · Micco (Google), 2016: 84 % of pass→fail transitions post-submit were flakes. [post](https://testing.googleblog.com/2016/05/flaky-tests-at-google-and-how-we.html) |
| Sleeps, timers and shared state as flake markers | Luo, Hariri, Eloussi, Marinov — FSE 2014: async wait 45 %, concurrency 20 %, order dependency 12 % of 201 fixes. [PDF](https://mir.cs.illinois.edu/lamyaa/publications/fse14.pdf) |
| Upkeep as a cost | Spadini et al. — ICSME 2018: smelly tests 47 % more change-prone. [PDF](https://sback.it/publications/icsme2018a.pdf) · Snapshot tests: 8.2 % of commits update snapshots in 569 Jest projects, ICSME 2023. The Palomba/Zaidman papers tying smells to flakiness were retracted — not cited here. |
| Staged, audited deletion with a restore path | Uber Testopedia: new → stable → unstable → disabled → deleted, a ticket on each move. [post](https://www.uber.com/en-US/blog/flaky-tests-overhaul/) · `qa-skills/test-suite-curation`: a restore command on each deletion. [repo](https://github.com/petrkindlmann/qa-skills) |
| Fold, and veto a shrinking kill set | `slobac` `semantic-redundancy`: one-sentence behaviour per test, fold into the canonical one, "lost kills are a veto"; drift guards as false positives. [repo](https://github.com/Texarkanine/slobac) |
| Timeouts are not kills | `cargo-mutants` exit code 3 masking missed mutants. [issue](https://github.com/stratalab/strata-core/issues/3225) |
| Trade a property only for a better one | Kent Beck, *Test Desiderata*, 2019. [site](https://kentbeck.github.io/TestDesiderata/) |

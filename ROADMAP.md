# systems comic — Roadmap

Where the project is headed. **The plan is this first section**; everything from
`Shipped` down is the record of what is already built, kept because the reasoning
behind each decision is worth more than the summary of it.

**Note on the shape of this file.** Most of it was written when the site was one
book, and the sequencing argument below still reasons about a one-book site. The
site is now a shelf: `/ddia` is book one, `/papers` is book two, the calculator
stands alone. That argument wants rewriting against how the two books are actually
being weighted, which is a decision, not an edit — so it is flagged rather than
guessed at. Everything else here has been brought back in line with what shipped.

## Next up

Two things here are waiting on a decision — the cost calculator and which book starts
next — and the one thing that is not waiting on anything is telling anyone the book
exists. The three long menus further down — app sims, paper-driven components, the composer — are the
longer game, and the sequencing note at the end of this section says why they are
not first.

**The papers book is finished**, which changes what this section is for. It used to
be a writing queue. What is left is the cost calculator, one rejected experiment
kept as a warning, and the question of which book starts next — which is the one
that actually needs answering.

### The papers book — Season 3 is the map

**Season 3 is up as a contents page**: thirteen chapters and a close, nothing
written. The first two seasons argue about data, and both assume without
arguing that a broken machine has *stopped* and that the machine itself is
free. Season 3 reads the papers underneath that — FLP, Chandy-Lamport, partial
synchrony, the Byzantine papers, and the scheduling and caching classics.

It also closes a hole the adversarial pass found and did not fix. #84 caught
Chapter 23 claiming six times that Chapter 7 covered Chandy-Lamport; the
sentences were corrected and the absence stayed, because the algorithm is
genuinely not in this book. FLP was missing on the same terms — two chapters
about reaching consensus with no impossibility result underneath them.

Source: the CS 525 reading list (UIUC, spring 2026). Compared paper by paper,
**9 of the 82 papers it names are already chapters and 73 are not**, which is
what made this worth doing as a season rather than as a duplicate. The 2025
frontier is deliberately left alone — a paper from this year is a claim and a
paper from 1985 is a fact — and the ML systems half stays book D's, which this
file already assigns by name.

### The papers book — Seasons 1 and 2, and what they cost to finish

**31 chapters, both seasons, 30 papers plus a prologue that reads three more.**
Season 1 is where data lives, Season 2 is what happens when it stops sitting still.
The last chapter shipped at #81 and the review round closed it at #84; the progress
counter derives itself and now says *both seasons finished*, because "0 still to write" is the sort of line a reader assumes is a bug
and "complete" claims something nobody has decided.

Four things learned across it, worth not re-deriving:

- **A half-chapter is a real unit and should look like one.** Ch 2 is two decisions,
  five steps, nine minutes, no animated trace — because the thing worth animating in
  it (the shuffle) is already animated in the other book. A "short chapter" that is
  just a full chapter with less in it reads as unfinished; a half-chapter with its
  own shape does not.
- **Never draw a figure the other book already draws.** Cross-link instead. The two
  books share a skin and a vocabulary precisely so this is cheap.
- **A book ending in a disagreement has to hold both sides.** Ch 29 and Ch 30 start
  from the same observation and reach opposite conclusions, and the close says so
  rather than picking — the two chapters read better as a diagnostic than as a
  choice, and re-arguing them on the close page would have wasted both.
- **The review round had to be two passes, not one.** They ask different questions
  and merging them means doing neither properly. The de-AI pass (#80) asks whether
  the prose sounds written; the adversarial pass (#84) attacks what it asserts. Each
  found things the other structurally could not.

### The two review passes, and what only a person could catch

Recorded because the method transfers to every book on the shelf below.

**The de-AI pass (#80)** is evidence-driven: `voice.test.ts` compares chapters
against each other rather than against a standard, because a tell that only exists
at book scale is invisible in a diff. It found twenty-one chapters opening their
designer block with the same bare count and ordinal list, four consecutive finales
on the same beat, one sentence appearing verbatim in two acts. The trap on the way
out is worth keeping: replacing "Three decisions. The first is…" with "The opening
question is…" in eleven chapters is the same architecture with a new label, which
is exactly what the house rule bans — so the guard forbids *leading* with a
positional phrase rather than setting a threshold, because a threshold would have
papered over the difference between a label and a claim.

**The adversarial pass (#84)** downloaded all 41 primary PDFs and checked the book
against them rather than against memory: 429 numbers, 27 multiplier claims, 181
prose cross-references, 31 citations, 110 quotations, 141 links. Eight things did
not survive. The worst was structural rather than numeric — Chapter 23 asserted six
times that Chapter 7 covered Chandy-Lamport, and Chapter 7 is Lamport 1978, which
never mentions it. **Three of the eight are now guarded and the big one cannot be**,
because catching it needs a model of what each chapter contains. That is the
argument for doing this by hand on any book that ships from here.

### Book three — Kubernetes, built as a map and rejected

**Shipped as #88 and #89, closed unmerged.** Not a scoping problem and not a
missing chapter. The premise did not survive contact with its own sources, and
this is a record of what killed it rather than a plan to try again.

The pitch — the one this file made — was that Kubernetes is unusual among
infrastructure in having its *why* published, so the book inherits the
papers-book method. Reading the three answer keys before writing anything:

- **Three of the five Act I chapters read the same 24-page ACM Queue article.**
  That is a magazine piece, not a peer-reviewed paper.
- **The other two read Borg and Omega, which are not Kubernetes.** Using a paper
  about a predecessor to explain a system is the sentence-level error #84 found
  in book B, committed at the scale of an act.
- **Nine of fourteen chapters had no paper at all.** The words "kubelet" and
  "extensib" do not appear in that article.

Strip the answer-key framing and what remains is a book about Kubernetes
internals — a fine book, and not this site's, because the method here is read
the primary source and design it yourself. Two further strikes: reading source
is book F's format, and the boundary rule says three books arguing over one
territory is how a shelf turns into a pile; and **Kubernetes moves**, so a book
pinned to 2026 API machinery ages exactly the way a price list does, which is
the maintenance class this file already refuses for the cost calculator.

**The rule worth keeping, because it generalises to every book below: a book
needs a primary source per chapter, or it is a different kind of book and has
to say so before it starts.** The check is cheap — download the sources, grep
them for the words the chapter list promises — and it costs a day rather than a
season.

What survives: the Terraform comparison. Kubernetes observes the world every
loop; Terraform keeps a state file it believes; drift, `refresh`, `import` and
state locking all fall out of that one difference, and so, in the other
direction, does Kubernetes having no preview and no approval gate. That is an
idea comic in book A. The planning notes and the three PDFs are in
`notes/2026-08-18-kubernetes-book-plan.md`.

### A third calculator: cost

**This one needs a conversation before it needs code.** The framing below — *ratios,
not prices* — is my answer to the maintenance problem, not an agreed one, and it is
the whole design. If the ratio framing is wrong, nothing under it survives.

The case for it being its own page rather than a column is the same one that kept
capacity and latency apart — **it is a different shape.** Capacity is division,
monotone and safe to extrapolate. Latency is a hockey stick that goes vertical well
before the ceiling. Cost is **linear when you rent and a staircase when you buy**: you
never pay for 1.3 machines, and that discontinuity is the lesson. It is also the only
one of the three whose answer can invert an architecture — capacity says "you need a
cache", cost says the cache outprices the database it protects, or that **egress
dominates the bill and appears in no capacity model anywhere.** Against the
`$0.023/GB-month` already in the S3 envelope, reading a GB out once costs roughly 4×
storing it for a month.

**The risk, which is unlike anything else on this site: prices expire.** Every other
constant here is physics or a published measurement — the speed of light is not
repriced, and Netflix's 1.1M writes/s stays true as a historical fact forever. A price
list is true until a vendor changes it, and then the page is silently wrong with no
error anywhere. That is a different maintenance class from the rest of the project.

**So build ratios, not prices.** Egress ÷ storage. Per-request price ÷ object size —
the small-object tax the S3 page already computes, where a 1 KB object costs ~18× its
monthly storage on *every* read. Managed ÷ self-run. Cloud-year ÷ purchase price, and
where the crossover lands. Ratios move far more slowly than absolute prices, and the
architectural decision lives in the ratio anyway. Absolute dollars go behind one dated
constants table carrying the same `MEASURED` / `ASSUMED` treatment as everything else.

Anchors for the reality tests, in the established style: Dropbox's S-1 (~$75M saved
over two years moving off S3), 37signals' published repatriation numbers, and the COST
paper already cited on the web deep-dive. A second win: `estCostUSD` in the
observability sim is currently `~$0.10/GB` with no source — the weakest number on the
site — and would import from a real model the way the latency page imports from
capacity instead of restating constants.

### The calculator's basic view — built, rejected

**Built on `calc-basic-view`, PR #46, closed unmerged. Sam did not like it.** Not a
scoping problem and not a missing toggle — the thing itself did not earn its place, so
this is a record of what was tried, not a plan to try it again. Anyone reaching for
"let's simplify the calculator" should read it as a warning first.

The mechanism, because it worked and is worth not re-deriving: `fold(v, req)` moves every
input one rung either way and keeps it visible only if the page changes its mind about
something — the store, the components, the shard count. The five presets folded to **7–12
visible out of 29**. Computed rather than hand-picked, which earned its keep: `fsync` is
load-bearing on a social feed and inert on metrics ingest, so any frozen "basic list" is
wrong for one of them. As a pure function of `(v, req)` a shared link folded the way it
folded for whoever sent it.

Two findings that outlive the feature:

- **A fold must be stricter than the sensitivity panel beside it.** That table forgives a
  shard count that drifts without doubling, because flagging every wobble would bury the
  assumptions that flip a decision. A fold cannot: *"hidden, and it only moves the number
  you are reading by forty percent"* is the sentence such a feature exists to never say.
  The first version shared `diffOutcome` and the tests caught it immediately.
- **Fold the control, never the number.** Every value stayed printed in the workings
  column, so the page's claim — the arithmetic is on the page and you can check it —
  survived. The guarantee was narrower than "nothing changed": *nothing hidden can change
  the architecture*.

What it got wrong, on the evidence: it had no affordance — the panel simply had fewer
sliders in it, and the only sign anything was withheld was a note below a dozen controls.
Asked "where is the basic view?", the honest answer was that there was nothing to see. But
that is a description of one flaw, not a fix list. **The page is thirty sliders on
purpose**, and the wall of constants is part of what makes it trustworthy; that is the
prior any future attempt has to argue against.

### Sequencing — why none of the big menus are first

The composer's own gate says to build it only once the component library is rich
enough to be worth composing, and **six flagship deep-dives and twelve comics already
clear that bar.** A seventh component makes the site longer, not better. Meanwhile the
two weakest surfaces are the experimental sims and comic comprehension, and both are
about how the depth that already exists *lands*. So: sharpen before building. The
composer stays the exception, because it is the synthesis rather than more of the same.

**What the finished papers book changes about this.** The argument above was written
when one book was mid-flight and everything else had to wait behind it. Nothing is
mid-flight now, so the queue is no longer self-evident and the next move is a choice
rather than a continuation — which is exactly the decision flagged at the top of this
file and at the foot of the shelf below. **It has not been made, and this file should
not pretend otherwise.**

### Loose ends

- **The book is finished and nobody knows.** Every remaining item here is
  building; none of it is telling anyone. That is now the largest gap on the list,
  and it is a different kind of work from the rest of this file.
- **`calc-basic-view`** is the one branch still on the remote — the basic-view
  experiment above, kept because the code and its 26 tests are there if it is ever
  wanted. The three merged branches this line used to list are gone.

---

## The shelf beyond the papers book

The site is a library now, so this is the list of books, not features. All of these
are prospectuses — nothing below is started, and the gate they were waiting on has
long since passed: the format is proven across two finished books, and the machinery
(`DesignIt`, `ChapterView`, `TracePlayer`, the geometry lint, the card renderer, the
voice and cross-reference guards) is shared rather than per-book. **A third book now
inherits more than the second one did**, which is an argument for starting one and
also the reason to be careful about starting three.

**The library-wide theme, stated once so each book can stop restating it:
hardware physics forces design.** Sequential beats random, the memory hierarchy is a
cliff, the network is scarcer than the disk, and every architecture in every book is
somebody paying one of those tolls.

### The next book: *Computer Architecture: A Quantitative Approach*

Hennessy & Patterson, over CSAPP and over a compiler book. Working title
**"Why Your Code Is Slow"** — a placeholder, on the same terms the papers book's
title was a placeholder until it wasn't.

**Why this one, out of the three.** It is not a new method for this site — *it is
where this site's method came from, made explicit.* Two habits were lifted from it
already and are load-bearing on pages that have shipped: **Amdahl's law on the
ceilings** (each store binds on one wall while another idles, so the verdict prints
the distance to the first wall *and* the ratio to the second), and **report the
sensitivity, not just the estimate** (move each constant one rung, re-run, list only
what changes an answer — which caught a live ranking bug). The capacity calculator
is already a quantitative-approach instrument built by someone who had read the
book. A book about the book would put a name on what the rest of the shelf is
quietly doing.

It also has the best interactive surface of the three, and that is not a small
point. Caches, branch prediction, pipeline depth, the roofline model, the memory
hierarchy — every one of them is a **slider against a ceiling with a meter on it**,
which is the exact widget vocabulary this site already owns. Nothing new would need
inventing to make the first chapter interactive.

**Why not the other two.**

- **CSAPP** overlaps two books that are already on this list. Its OS half is Book F
  (xv6, which reads source rather than papers) and its concurrency half is Book E.
  Three books arguing over the same territory is how a shelf turns into a pile.
- **A compiler book** is a real book and its natural home is *inside* Book C — the
  analytical engine already covers vectorized-versus-compiled execution and a
  Cascades optimizer, which is the half of compilers this audience came for. The
  other half wants a code editor and an IR view, which is a different application,
  not a different chapter.

**Boundary rule, so it does not eat the others:** this book owns *why the hardware
makes that slow*. Book B owns *why the system exists and what it traded*. Book C
owns *how the engine executes*. It sits underneath all of them, which is also the
argument for its chapter order — it should be readable by someone who has read none
of the rest.

### The one with a different format: the GPU book

**Programming Massively Parallel Processors**, Hwu, Kirk & El Hajj. Note the timing
before buying anything: the **5th edition shipped 27 February 2026**, adding wavefront
algorithms, a multi-GPU chapter and advanced matrix-multiply optimisation. That is the
one.

Chosen over CSAPP and over a compiler book, and the reasoning is the same shape as
the architecture pick above. **CSAPP overlaps two books already on this list** — its
OS half is Book F and its concurrency half is Book E, and three books arguing over
one territory is how a shelf turns into a pile. **A compiler book's best half already
lives inside Book C**, which covers vectorised-versus-compiled execution and a
Cascades optimiser; the other half wants a code editor and an IR view, which is a
different application rather than a different chapter. PMPP is the only one of the
three that is simultaneously a real textbook and a hands-on course, where every
chapter is a kernel you write and then measure.

**This is the first book on the shelf whose format has to break.** Every other book
says *read the idea, then push on it until it breaks* — a slider, a trace, a
recomputed verdict. That is the wrong verb here. A GPU book has to say **write the
kernel, run it on your own hardware, and watch the roofline move.**

Which is now possible in a page: **WebGPU compute shaders**. Not CUDA, but the model
maps almost one-to-one — workgroup for block, workgroup storage for shared memory —
and coalescing, tiling and occupancy behave the same way. Naive matrix multiply, then
tiled, then measure the speedup, **on the reader's own GPU**. No other book here can
say the numbers on screen are the reader's own machine. Per-chapter escape hatch to a
Colab notebook for the real CUDA version, because some things genuinely need a T4.

Two things to design around rather than discover later:

- **WebGPU is not universal.** Chrome and Edge are fine, Safari from 26, Firefox
  partial. Needs a static fallback that still teaches the chapter, not an error.
- **Browser GPU timings are noisy and sandboxed.** So the receipts have to be
  **ratios and shapes** — this kernel is 6× that one, the curve flattens here — and
  never absolute GFLOP/s. The same discipline the cost calculator needs, arrived at
  from a completely different direction, which is mild evidence the house rule is
  right.

**What it deliberately does not cover:** NVIDIA as a *product* ecosystem. No TensorRT,
no Triton Inference Server, no NCCL topology, no Hopper-era TMA. Pair the book with
primary sources for that — the CUDA C++ Programming Guide and the architecture
whitepapers — and note the boundary with **Book D**, which already owns the
inference-serving end (FlashAttention, vLLM, PagedAttention). Book G owns *why the
hardware makes that slow*; this one owns *how to make a throughput machine actually
go fast*; Book D owns *what people run on it*.

**The honest cost, because it is the most expensive prospectus here.** Every other
book on this list inherits a finished machine — `ChapterView`, `DesignIt`,
`TracePlayer`, the geometry lint, the card renderer — and is therefore mostly
writing. This one needs a WebGPU runner, a kernel editor, and a benchmark harness
whose numbers are trustworthy enough to print. That is a new interactive surface, not
a new skin on an existing one, and it should be planned as such rather than
discovered in chapter two.

### The one where there is no canonical book: Kubernetes

Asked for on 2026-08-16, with the bar set at *expert and beyond*. The honest thing
to say first is the thing that makes this book different from every other entry
here: **there is no DDIA for Kubernetes.** No single volume that a competent
practitioner reads and comes out the other side an expert. The genuinely expert
material is the API machinery, the KEPs, and the source, and every book on the
shelf is either an introduction or a snapshot of a version that has since moved.

So the pick is two books doing different jobs, and a set of papers doing the job
this site actually cares about.

**The spine — *Programming Kubernetes* (Hausenblas & Schimanski, O'Reilly 2019).**
Because it teaches the one idea everything else is derivable from: you write a
controller, watch the API for a desired state, compare it to the observed state,
and act. Level-triggered, not edge-triggered; no transactions across objects; the
API server is a database with admission control in front. Once that clicks, the
scheduler and the kubelet and every operator you meet stop being separate things
to memorise. It is aging — client-go has moved and controller-runtime is the way
people build now — so read it for the model, not for the imports.

**The substrate — *Core Kubernetes* (Vyas & Love, Manning 2022).** The layer the
first book stands on: kubelet, CRI, CNI, CSI, etcd, how a pod actually gets a
network. This is the operations-and-internals half, and the half that answers
"why did it do that" at 3am.

**The answer keys, which are where this site's method fits.** Kubernetes is
unusual among infrastructure: its *why* is published. **Borg** (EuroSys 2015),
**Omega** (EuroSys 2013), and above all **"Borg, Omega, and Kubernetes"** (ACM
Queue 2016), which is the Google team explaining what they got wrong twice before
getting here. That is exactly the shape Book B already uses — read the constraint,
design your answer, then check it against the paper — which means **this book
inherits the papers-book machinery rather than breaking format the way the GPU
book does.** DesignIt, citation cards, TracePlayer, all of it.

The chapter spine writes itself from that: *why level-triggered rather than
edge-triggered* · *why no transaction across two objects* · *why the scheduler
does not talk to the kubelet* · *why every extension is the same shape as the
built-ins*. Each has a real answer, and the hands-on layer is trivially available
in a way the GPU book's is not — `kind` runs a cluster on the reader's laptop, so
"write a controller and watch it reconcile" is a chapter, not an infrastructure
project.

**Cost:** cheap, like C–F. It needs writing and SVGs, not a new interactive
surface. Filed on the cheap side of the split below.

### Still on the shelf as prospectuses

- **Book C — "The Analytical Engine"**: single-node engine internals, scaffolded on
  CMU 15-721. Layout → vectorized vs compiled → morsel scheduling → Cascades →
  Snowflake/Photon/Velox/DuckDB. *"You are the engine designer"*, with in-browser
  benchmarks as the receipts.
- **Book D — the AI storybook**: the ideas line (perceptron → Transformer → GPT-3 →
  RLHF) with the system moments woven in, then the machinery (Megatron/ZeRO/FSDP,
  FlashAttention, vLLM/PagedAttention, quantization).
- **Book E — concurrency**: Dijkstra → Hoare → Hewitt → Lamport → Herlihy → memory
  models → Go/Erlang/async → Rust `Send`/`Sync`. The actor act doubles as the bridge
  into Book B, via Akka and Orleans' virtual actors.
- **Book F — the OS storybook, on xv6**: a different format, reading *source* rather
  than papers. The machine's illusions built one at a time. It is the root book —
  WAL, buffer cache, page tables and the scheduler all start here and every other
  book borrows them.

**Sequencing across books, which is the part that needs deciding rather than
writing:** shipping chapter one of a new book is cheap now and finishing a book is
not, so the failure mode is six books at three chapters each. Whatever the answer
is, it should be a rule about *when a book is allowed to start*, not a ranking of
which is most interesting — every one of these is the most interesting on the day
you start it.

One input to that rule, now that there are three entries above rather than one: the
books split cleanly into **the cheap ones and the one that isn't.** C, D, E, F, G and
the Kubernetes book all inherit the finished machine and are therefore writing plus a
few SVGs. The GPU book needs a new interactive surface built first. That is not an argument against it
— it is the argument for deciding *when*, deliberately, rather than starting it on an
enthusiastic afternoon and discovering the cost in chapter two.

## Shipped

- ✅ **Season 2, and the book finished** (#62–#79, #81, #84). Thirteen chapters from
  Spark to the unbundling essay, an epilogue whose two chapters disagree on purpose,
  a close that holds both, and **Chapter 0 last** — the prologue, written after the
  rest, because a chapter about the three ideas every later chapter spends is easier
  to write once you know which ones they were. Four structural calls worth keeping:
  the staleness ladder is the season's spine, Borg went to the Kubernetes book rather
  than here, CRDTs got one chapter rather than an act, and both epilogues shipped on
  probation and earned their place.
- ✅ **Every figure in the book was rendering at about six pixels** (#82, #83). One CSS
  rule: the figure sat in a column capped at 340px against a 344-unit canvas, so a
  5-unit label rendered at roughly its own number in pixels. **81 figures out of 81**
  had type under nine pixels. The geometry lint had been driving a real browser over
  all 50 pages for months and could not see it, because it measures the drawing in
  its own coordinates where the layout is perfect at any size — the canvas has no
  idea how wide the page will draw it. `TYPE-TOO-SMALL` compares each label's font
  size against the scale the page actually gave its canvas; restoring the old column
  produces 929 violations. The same rule from the other side left **29 empty grid
  cells** beside half-width panels. Then #83 fixed what #82 caused: at full panel
  width the figures' own labels came out at 16.4px against 15.5px body text — a
  caption shouting over the sentence explaining it — so they are capped at 660, which
  is about where the prose measure stops, and the figure now follows the opening
  paragraph instead of arriving after the argument it was meant to carry.
- ✅ **Say whose book it is before the reader has to scroll** (#85). `/ddia/read` led
  with *"inspired by DDIA, 1st edition"* and kept *unofficial* and *not affiliated*
  twelve cards down. The comic pages were worse and are the same route: they render
  no SiteFooter at all, so a kicker reading "Inspired by" was very nearly the whole
  of it, on the page a shared link is most likely to open. The guard tests
  **position, not presence** — presence was already true and was not enough.

- ✅ **The calculator's presets toured two of its six columns** (#50). Sam noticed that
  everything seemed to land on wide-column. Measured: three of five presets did, the other
  two landed on sharded SQL, and **three stores were never shown winning anything**. Nothing
  was broken — every individual answer was right — but a six-column table demonstrated two,
  and `loss: 'rebuild'` was set by no preset at all, so the requirement that unlocks the
  in-memory column was unreachable from the guided path.

  The fix was **not** a workload per store, which was the tempting version. Working
  backwards from an answer would inverse the page's own argument — requirements filter,
  load ranks, ceilings force — into a lookup table, and imply each store has one canonical
  use, which is the folklore the page exists to replace. What changed is the *set*: two
  ordinary systems that were missing. An **internal/B2B app** at 50k users, which reaches
  single-primary SQL and teaches the site's most under-taught lesson — you may not need to
  shard anything. And **sessions / rate limits**, the one honest workload where durability
  stops being a filter.

  Two columns cannot be reached and never will be: swept all **64 requirement combinations
  at four load scales**, and Document and Columnar win **zero**. That is by design — the
  model already said so in each store's `chooseFor` — so the page now says it where the
  reader would otherwise wonder, and `presets.test.ts` re-derives the claim by brute force
  rather than trusting the prose. If the model ever changes so one of them can win, the
  test fails and says to delete the line.

  Also checked while there: the ingest preset's **332 shards** is arithmetically right —
  50M devices x 200 events/day x 2 KB over 6 months is ~3.2 PB, which is 324 nodes at 10 TB
  each. A big number, not a wrong one.
- ✅ **The observability sim's cost KPI was wrong by 1000x** (#48). Chasing the roadmap's
  own loose end — `estCostUSD` at `~$0.10/GB` with no source, "the weakest number on the
  site" — turned up something worse than an unsourced constant. The function multiplies GB
  by dollars-per-GB and returns **dollars**; the page formatted the result as though it
  were **thousands**. Every figure on screen was a thousand times too big: a $664 bill
  printed as `$664k / month`.

  It survived because it looked right. A six-figure observability bill is an entirely
  believable thing, so nothing about the page invited a second look — which is the whole
  argument for pinning arithmetic to a case worked out by hand rather than to whether the
  output seems plausible. `cost.test.ts` does that now, and its second test is the one the
  bug could not have survived: one GB/day, ingest only, is **three dollars**.

  The constants are named, dated and marked *assumed* on screen rather than sitting inline
  — prices expire in a way the physics elsewhere on this site does not. The amber threshold
  was an absolute `> 400` that a units fix would have left permanently lit; it is now twice
  what the stage opened at, which is both repricing-proof and the actual lesson the
  retention slider teaches. The durable claim is the **ratio** — hot storage ~10x cold —
  and that is asserted rather than described.
- ✅ **The two sims run on one engine again** (#45). They had been running on *copies* of
  one engine — 973 and 927 lines differing in 118 — for long enough that the observability
  copy still opened "Feed at Scale", still declared a class named `FeedEngine`, and its
  model carried two shims written for a shared engine that did not exist. 1,900 lines
  became 1,264, and the geo-map subsystem moved into the feed, the only sim with map stages.

  Verified by pixel-diff rather than by argument: seeding `Math.random` and pumping rAF by
  hand makes a run reproducible frame-for-frame — two runs on `main` came back
  byte-identical, which is what makes the comparison mean anything. Every feed frame was
  unchanged; every observability frame differed in exactly one 52×12 box, the node caption,
  changed on purpose. **That caption was the fork's real damage:** the observability engine
  had inherited the feed's `subLabel`, so it branched on `pgP`, `redis` and `kafka` — kinds
  no observability pipeline has — and had no branch for the indexer it draws. The visible
  symptom was an indexer reading `6×` while federation gave it 8× the slots.

  `engine.test.ts` now checks each sim's hooks against its own model. **The first version of
  that test passed against a deliberately broken engine** — it matched `kind === '…'` with
  single quotes and the bundler rewrites literals to double quotes, so it matched nothing
  and reported success. Third appearance of this class of bug here, and the reason every new
  guard gets broken on purpose before it is trusted.
- ✅ **Comprehension: the whole track, and two verification tools that were lying.**
  Six PRs against the audit finding that some pages "are not that straight and easy to
  understand enough".
  - **Quorums say what they do not do** (#30). Leaderless writes are not sequenced by
    anything, and `W + R > N` guarantees a read *sees* every candidate value while
    saying nothing about which is right. Freshness and resolution are different
    problems, and the page had let them read as one.
  - **`concurrent(v1, v2)` is no longer magic** (#36). The call was on screen with
    nothing behind it; version vectors were named three times and defined none. Now
    defined in the `deeper` fold-out with a two-counter-map figure — and kept out of
    the Rung 1 body on purpose, since Cassandra is last-write-wins and DynamoDB
    dropped vector clocks, so most readers will never operate one.
  - **In-the-wild bullets can carry a figure** (#33, #34). `InTheWild.points` was typed
    `string[]`, so the wall of text was a wall *by construction*. Typed as
    `(string | WildPoint)[]`, then one figure per comic — not one per bullet, which
    would have been 49 drawings and a different kind of wall.
  - **Forward references, swept and then guarded** (#35). Two real gaps found; six of
    the ten "hits" were my matcher hitting `next: { slug }` nav links and the `term:`
    field name. `glossary.test.ts` now fails on a term used before the comic that
    defines it, and a second test asserts each of the three recorded exemptions is
    *still* a genuine forward reference — an exemption list nobody re-checks becomes
    a list of things that used to be true.
  - **Ch 6 companion — Choosing the Partition Key** (#43), the twelfth comic. The hole
    it fills, recorded because it is the strongest argument this project has for a new
    page: hash vs range is how DDIA *opens* Ch 6, before consistent hashing, and this
    site gave it two rows of a tradeoffs table — while **three shipped surfaces
    depended on the distinction and none taught it**. The capacity calculator's *first*
    requirement row is `Fetch one thing / Scan a range`, and its own info text calls
    the sort key "the most consequential schema decision you will make". The **hot
    range** is a full cascade trace on the S3 deep-dive — the date-prefix disaster *is*
    a timestamp partition key — and the concept behind it got four words. **Compound
    keys** appeared once sitewide, as a fix in a Kafka runbook row. It was not new
    surface; it was a hole under existing pages, which is why it earned an exception to
    "sharpen before building". Deliberately *not* bolted onto the consistent-hashing
    comic, whose single misconception is clean and would have been blunted by a fifth
    step about a different decision. Hash → what hashing costs (scatter-gather, which gets
    *worse* as you add nodes) → what sorting costs (the hot range, and the clock only
    moves one way) → the compound key. Local vs global secondary indexes went in the
    fold-out rather than becoming a fifth step. Its index card shipped blank for one
    commit, saying "in the sketchbook" beside a working link; `index-page.test.ts` now
    asserts every comic has a card, under the title it advertises, with a panel drawn.
  - **Two tools were passing without checking anything.** `npm run check:diagrams`
    reported OK while measuring **zero** diagrams — it had been green through an app
    that 500'd on a duplicate export. It now opens every `<details>` first
    (`getBBox()` returns zeros in a `display:none` subtree, so a figure in a collapsed
    bullet measured as a point at the origin), fails on any page error, fails if a
    comic yields no diagrams, and prints the count. Separately, **`npx tsc --noEmit`
    checks nothing here** — `tsconfig.json` is solution-style (`"files": []` plus
    references), so it exits 0 having verified nothing; the real gate is
    `npm run typecheck` (`tsc -b`). Every "typecheck ✓" from the wrong command was
    vacuous.
- ✅ **The calculator's own correctness** (#32). Two findings from tracing the
  requirement filters, and neither is a CAP problem — **CAP cannot bind on that panel
  at all, because none of the seven requirements asks about availability.** You cannot
  violate a theorem whose third term you never requested, and "must be current" is
  read-your-writes on the primary path, not linearizability. That is now said out loud
  in "what it will not tell you".
  - **Nothing enforced that a survivor exists.** No combination empties the candidate
    list, but only because sharded SQL passes every filter *structurally* — an
    accidental universal survivor. Had `alive` ever emptied, `alive.reduce(…, alive[0])`
    seeds with `undefined` and the `!` asserts it away: a crash or silent garbage, not
    a graceful "nothing fits". All **64** combinations are now swept at three load
    scales, plus a canary that names `sqlShard` as the store the guarantee rests on —
    so if the thing holding it up changes, the test says which thing.
  - **"Must be current" contradicted "who else must see each write".** Derived systems
    are fed asynchronously — that is why the page starts recommending a log at two of
    them — so *must be current* cannot be true of the copies at any budget. The tension
    is surfaced where the two rows meet.
- ✅ **The sims got a correctness floor** (#37, #38). They had no tests at all. The
  harness reads each mission goal's **source** rather than calling it, because `&&`
  short-circuits and a goal can pass without ever reading the control it claims to be
  about. It immediately found one: a break-it-then-fix-it mission whose payoff goal was
  **already ticked on arrival**. Separately, sparse stages drew a handful of nodes
  adrift in a large canvas; both engines now compute a zoom in `layout()`.
- ✅ **The launch checklist, closed** (#54–#58). Per-page social cards: 31 now, for
  60 routes — legacy aliases share their canonical's by object identity, and the
  build *fails* if a route has no card. Putting all of them on one contact sheet is
  what caught `/ddia/read` still describing itself as "Eleven ideas", the third
  hand-maintained tally in this repo to go stale. Cloudflare: HTTPS enforced, `www`
  resolving and redirecting, query strings preserved — verified against the live
  domain rather than the dashboard, after I read a cached 301 and reported a
  redirect as broken when it had been fixed. The repo became `systems-comic` and the
  README lost 79 lines, including two sections that argued for the site instead of
  pointing at it.
- ✅ **The papers book, Act I** (#60, #61). GFS and MapReduce, either side of the
  Bigtable chapter that had been carrying the book alone — and Bigtable's premise is
  that it is *the database GFS deserved*, so Act I only worked if you already knew
  the paper underneath it. Three findings outlived the chapters. **The geometry lint
  had never looked at the papers book**: it walked a hand-written array of comic
  slugs, so Bigtable's figures had never once been measured; it reads the route
  table now, 65 diagrams across 12 comics → 70 across 15 pages. **`DesignIt` renders
  option labels raw** while the question and the answer go through `rich()`, so
  `only *what*` printed its asterisks — invisible in the source, obvious in a
  screenshot, and now four tests. And **"1 of 18 chapters live" was typed by hand in
  three places**, all wrong the moment Ch 1 shipped; derived now, with the check that
  matters running in both directions, because a chapter can be finished, registered
  and routed while its TOC row still says unwritten.
- ✅ **Sharing, and one thing I got wrong about how to take a request** (#39–#42).
  Calculator state now lives in the URL, so a dialled-in scenario is a link — the model
  is a pure function of its inputs, and that claim was unusable while the inputs could
  not travel. 24 routes carry their own title, description and card tags, emitted as
  flat `dist/<route>.html` at build time (scrapers do not run JS; and the
  `<route>/index.html` form makes Cloudflare **307** to a trailing slash first — found
  by running real `wrangler dev`, not by reasoning about it). Two bugs worth keeping:
  `Number('')` is `0`, not `NaN`, so a truncated `?dau` link silently set daily actives
  to the bottom rung; and constants the page decides for itself leaked into shared
  URLs until `DECIDED` was threaded through both encode and decode.

  **The process mistake:** Sam asked for a share-to-social button. I reframed it into
  URL state and OG cards, wrote *my* version into this file titled "buttons last" with
  a line arguing "share on X" does not travel — and built that. The reframe was worth
  having; substituting it for the request was not. The button was then built (#40) and
  removed at Sam's call (#41), along with the calculator's copy-link. **A reframe goes
  alongside the request, not instead of it.**
- ✅ **The concept lens is drawn — 11 of 11 ideas live** (twelve now, with the Ch 6
  companion above). Part I gained **Ch 1 · Tail
  Latency** (the average is nobody's experience; `1 − 0.99¹⁰⁰ = 63%` for fan-out *and*
  for a 100-request session; hedged requests taking 1,800 ms → 74 ms; and why the cache
  did nothing for the tail). Part III gained both of its chapters: **Ch 10 · The Shuffle**
  (the sort in the middle is the job; broadcast and pre-partitioned joins as ways to not
  move data; one hot key making the cluster irrelevant — Amdahl in a third costume) and
  **Ch 11 · Stream–Table Duality** (a log is not a queue, which is the entire trick;
  compaction bounded by key cardinality rather than history; and dual writes as the bug
  the duality actually fixes — the same "one log, many consumers" the capacity page starts
  recommending at two derived systems). Nine new diagrams, all passing `check:diagrams`.
  Chapter numbers now say **DDIA 1st edition** everywhere they appear, since the 2nd
  edition renumbers. The book later opened an **extension shelf** — Part IV,
  "where the book points": chapters that start where the text stops, kept off
  Parts I–III so nobody mistakes them for Kleppmann's outline. It opened with
  three chapters. **Exactly-Once, Mechanically** (Ext 2: the retry that cannot
  tell a lost write from a lost ack; the end-to-end argument as the load-bearing
  idea; the sequence number and the transactional offset-plus-output commit;
  and "once is per sink" — the guarantee ends at Kafka's door). **The Rebalance**
  (Ext 3: one-partition-one-owner and what the stop-the-world protocol spends
  to keep it; the two timers; eager → cooperative → KIP-848's barrier-free
  reconciliation; the leader-consumer misconception). And first,
  **Backpressure** (Ext 1: drop /
  buffer / slow-the-sender as the only three exits; credit as the one mechanism under
  TCP's window, prefetch, permits and `request(n)`; the Chiu–Jain phase plane for why
  AIMD wins; and the pressure chain that ends with `send()` blocking the checkout API) —
  it exists because the Kafka papers chapter judges bare push and never says what the
  push camp built instead, and both deep-dives now point up at it.
- **Component deep-dives** — flagship, 9-chapter treatment per infra component.
  - ✅ Kafka (flagship template: abstraction → anatomy w/ animated traces → hardware
    envelope → scale up/out → ops runbook + failure cascade → large-cluster reference → papers)
  - ✅ Postgres (UPDATE trace through parser/planner/executor/buffer pool/WAL, MVCC +
    vacuum lifecycle trace, PG hardware envelope, read/write-asymmetry sandbox, pager
    runbook + idle-transaction cascade, Notion sharding reference + fleet trace)
  - ✅ Redis (event-loop trace, fork/COW persistence trace, one-core hardware envelope,
    hot-key shard sandbox, whale-key cascade + runbook, Redis Cluster fleet trace —
    first page built from the `scalelab-design` skill)
  - ✅ RabbitMQ (publish→exchange→queue→ack trace, BEAM/watermark anatomy trace,
    per-node envelope with the alarm line, two-ceiling scale-out sandbox,
    slow-consumer-freeze cascade + runbook, production-estate trace with the
    Kafka handoff)
  - ✅ Web / app tier (request trace through four queues nobody instruments — the
    kernel accept backlog and the pool checkout wait; the autoscaler as a control
    loop with 3–5 minutes of dead time; a slot-not-CPU envelope carrying the M/M/1
    multiplier imported from `latencyModel`; a scale-out sandbox that reports what
    the clones *multiply* — connections, deploy headroom, queueing; the retry-storm
    cascade as a metastable failure; and Stack Overflow's nine servers, where
    `L = λW` on their published counters gives ≈ 6 requests in flight per box)
  - ✅ S3 / object storage (a GET from SigV4 to first byte and a PUT showing
    durable-first/visible-second, which is where strong read-after-write comes from;
    an envelope for a service you do not own — rate limits and a price list, with
    the SDK connection pool and the small-object tax as the two ceilings nobody
    expects; a prefixes-and-CDN sandbox that reads the invoice as a capacity signal;
    the date-prefix cascade where retrying prevents S3's own repartition from
    finishing; 2013 → 2025 scale figures with the interface unchanged)
  - **All six components are now flagship**, so `CLASSIC_MODULES`, `ClassicModulePage`
    and the `/components/:key` catch-all are gone. `ModulePanel.tsx` is just the
    `Sandbox` widget now, and `types.ts` lost `ModuleDef`/`ModuleContent` for a single
    `SandboxContent`.
  - `sandboxes.test.ts` makes "drag every slider to both extremes" permanent: it sweeps
    all six `compute()` functions to both ends of every ladder and both corners, and
    asserts no rendered string says NaN/Infinity and no meter percentage is non-finite.
    It found a real one on its first run — a 0% target-utilization rung divided the web
    fleet size by zero and reported `Infinity` connections.
  - Next: the Topology Composer, or more components from the papers (Cassandra, etcd/Raft).
- ✅ **The comic diagrams are live — where the idea is about time.** Five of the 33
  panels move, because what they explain is a process: replication lag (writes
  crossing a gap that never closes, stale plate breathing), the LSM write path
  (memtable fills → flushes → compaction lands the merged file), a Raft election
  (votes arriving in sequence, then the majority beat), a timeout (heartbeats
  missing → "A is dead" → the zombie wakes, one 6s clock), and the partition
  stampede (keys in flight). The other twenty-eight stay still on purpose —
  motion on a structural drawing explains nothing the still frame didn't.
  Only `transform`, `opacity` and `stroke-dashoffset` are animated: none of them
  change what `getBBox()`/`getPointAtLength()` report, so `npm run check:diagrams`
  still measures shipping geometry (verified green with animations running). Every
  declaration is gated on `prefers-reduced-motion: no-preference`, and the
  reduced-motion render was checked **byte-identical** to the pre-animation
  diagrams. Reserved class prefix: `gn-an-*`.
- ✅ **Order-of-magnitude sliders everywhere.** Every sandbox on the site now snaps
  to a 1-2-5 ladder like the capacity calculator — no more "557k/s" implying a
  measurement, and no more "2,175.8 MB/s" claiming six significant figures built on
  a shrug. Derived readouts round to two significant figures (`fmt.sig`, `fmt.mbs`).
  Shared ladders + slider live in `src/deepdives/ladder.tsx`; `InputDef.min/max/step`
  became `InputDef.steps`. Not everything is a ladder — a count that is small and
  exact (3 brokers, RF 2, RAM in powers of two) is a *choice*, not an estimate, so it
  keeps every value. `inputs.test.ts` enforces two rules across all six sandboxes:
  every default sits on a rung (an off-ladder default renders the thumb on the
  nearest rung while the label prints the stored value — the panel contradicts itself
  before you touch it), and every ladder climbs.
- ✅ **Storage-first calculator.** The decision the tool exists to make is where data
  lives, so that decision is now decomposed into the four dimensions that actually
  differ — **data model · storage engine · distribution · atomicity scope** — across
  six real compositions (single-primary SQL, sharded SQL, document, wide-column ring,
  column-oriented, in-memory KV). "SQL vs NoSQL" is a marketing split, not a mechanical
  one; keeping engine and distribution separate matters because choosing an LSM engine
  used to silently choose ring-based partitioning too. Two requirements were missing and
  are now filters: **how reads find the data** (point lookup disqualifies the column
  store — a row lives spread across every column file) and **how fresh reads must be**
  (must-be-current puts the cache on the write path and rules out async replicas, which
  is where the tool could previously give confidently wrong advice). Transport is
  demoted: it only becomes a comparison table when something must be pushed. Guarded by
  tests that assert each dimension filters independently, and that stores sharing an
  engine tie on the numbers — so what separates them is the requirement, never an
  invented constant.
- ✅ **Reality-tested against published architectures.** The calculator's arithmetic is
  pinned to numbers real operators published: Twitter's 345k deliveries/s, WhatsApp's 2M
  connections per box, Netflix's 1.1M writes/s on 288 Cassandra nodes (per-node flat at
  10.9–11.9k, which is what linear scale-out means), Facebook's memcache paper, Uber's
  40M req/s cache at a 99% hit rate, Discord's wide-column ring, Slack's 2.3M QPS on
  sharded MySQL, and the published shard-split thresholds (Vitess 250 GB, Cash App 1 TB,
  Notion 10 TB per physical database). Each is a test, not a claim.
  **The most valuable finding was where the model is structurally blind.** Discord and
  Slack store chat with the same access pattern and made opposite choices; four companies
  (Uber, Slack, Figma, Instagram) justified their storage pick by operational familiarity
  and never by a technical capability. A page that scores only workload fit will
  confidently disagree with all four, so it now says so in "what it will not tell you".
  Resharding cost is stated with both extremes — Google's AdWords MySQL took "over two
  years of intense effort across dozens of teams", DynamoDB splits "in the order of
  minutes", and automatic is not free either (a Cassandra node measured 106 hours to
  stream 2.2 TB plus three weeks of compaction) — and deliberately not scored.
- ✅ **Every number traceable, and a sensitivity sweep that found a bug.** Four changes,
  all aimed at the same complaint: the verdict was a wall of prose in which "19 shards"
  and "8.7%" appeared as assertions. (1) The verdict is now **sections** — ruled out ·
  what is left by the time it reaches a store · a table of how close each survivor gets ·
  headroom · so — and every computed number is a **click that jumps to the ceiling it was
  divided by** and flashes that row. There is now a *Write stream* ceiling row, because
  the engine table had been measuring against a wall the reader was never shown.
  (2) Each column names **real products and one operator running it at a published
  scale** — Stack Overflow on one SQL Server primary, Slack's 2.3M QPS on Vitess,
  DynamoDB's 89.2M req/s Prime Day peak, Discord and Netflix on the ring, Cloudflare's
  6M req/s into ClickHouse, Facebook's memcache fleet. (3) The page states its **scope**
  up front — rates, bytes and machine counts against eight ceilings; *no* latency, money,
  correctness or skew — and that the answer is **a pure function, not a judgement**:
  same inputs, same output, every number a division printed beside it.
  (4) **"The numbers pick" is not "the only one that works."** Said outright, plus:
  pinning any surviving column now produces a computed diff of what that choice costs —
  its first wall, what stops being atomic, who owns the resharding, and which forced
  components change. Writing that diff exposed a component the page had never
  recommended: **a plan for transactions that cross a shard**, which fires for the
  ledger preset at 8 shards.
  Two habits borrowed from *Computer Architecture: A Quantitative Approach*.
  **Amdahl's law** on the ceilings: each store binds on one wall while the other idles,
  so the verdict now prints how far the first wall is *and* the ratio to the second —
  the entire budget any fix has to spend. And **report the sensitivity, not just the
  estimate**: every constant is moved one rung on its own ladder, the whole model
  re-run, and only the moves that change an *answer* are listed. It earned its keep
  immediately — it caught a live ranking bug where deciding the cache **per store** let
  a store cross the 30% threshold *because* it reads badly, collect the 90% discount,
  and then score better at reads than the store whose reads were cheap enough not to
  need one. "Worse at reads wins", for the second time. The cache is now decided by the
  read rate against one node's ceiling, so every column is judged on identical incoming
  load; the artifact is pinned by a regression test.
  **The comparison table was also unreadable, and measuring said why — it was not
  width.** Row labels took 183px of a 647px table (28% of the comparison spent on
  captions, because `nowrap` sized the column to its longest label), and every data row
  printed the same caption in all six columns: "misses only, behind its cache" ×6, "of
  3 GiB/s" ×5. A caption true of the whole row now belongs to the row, the label column
  wraps and is capped at 118px, and per-cell prose keeps only what differs. That alone
  took columns **69–82px → 81–95px** and the table **781px → 577px tall**, with every
  cell one or two lines instead of four to seven.
  Widening the page was tried and **reverted**: the columns did get roomier (115–132px),
  but the page then carried two measures, and every panel had to be re-balanced around
  the wider one — half-empty prose cards, a note flowed into columns, a word-break rule
  that leaked out and split "VERDICT" into "VERDIC/T". More cost in consistency than the
  columns were worth. The sandbox split is now explicit (`minmax(280px, 344px) 1fr`)
  rather than falling out of whichever table had the widest min-content.
  Kept from that detour, because they were real bugs: grid items get `min-width: 0`, the
  output tables wrap instead of setting a min-content floor, and the two prose-wide
  tables scroll in their own boxes — so the page no longer scrolls sideways at any width
  (it did before, from ~1000px down). Only genuine jargon carries a gloss: "hand-rolled"
  gets an info icon (no middleware — the application works out the shard itself; Notion
  by workspace id, Figma via a proxy it spent nine months building), while PostgreSQL and
  Cassandra do not need one. Each store's scale claim links to the post it came from.
- ✅ **The latency budget** (`/calculator/latency`) — a second calculator, deliberately not
  merged with the first. Capacity is division: load over ceiling, monotone, safe to
  extrapolate. Latency is a hockey stick that goes vertical well before that ceiling — at
  43% of a capacity ceiling you are already waiting three-quarters of your service time in
  a queue — so one panel implying they behave alike would hide the single most important
  fact. Two routes under one nav item, because a tab held in component state cannot be
  linked and a fifth nav item would worsen the ≤700px overflow.
  You state a p99 target and the page **spends** it: **physics floors · hops add ·
  utilization multiplies · fan-out amplifies the tail**. It names the largest term and
  ranks the fixes in milliseconds. It refuses to predict a p99 — a queueing network with
  assumed distributions is confidently wrong — so every term is closed form and the one
  assumed distribution (the tail shape pricing fan-out in ms) is marked and shown.
  **The useful half is "what will not help":** a cache does nothing for your p99 until the
  hit rate passes 99%, because below that a p99 request is by definition a miss; no amount
  of capacity touches the speed of light; a faster median is nearly invisible under fan-out,
  where you need one server's p99.99. Anchors as tests: Dean & Barroso's 63% reproduces
  exactly (1 − 0.99¹⁰⁰), a 100-way fan-out needs p99.99 (0.99^(1/100)), NY–London is
  55.85 ms theoretical / 78 ms routed against a published 70–80 band, and the datacenter
  floor is napkin-math's measured 500 µs rather than the wire.
  Constants and controls are imported from the capacity page, never restated. Its ladder
  invariant immediately found a **live bug there**: `fsync` defaults to its measured 300 µs
  while `L.us` went …200, 500…, so that thumb had been rendering on 200 while the label read
  300 µs — `inputs.test.ts` only ever walked the six sandboxes, never the calculator.
  The cross-link is the point of keeping them adjacent: every component the capacity page
  forces is also a hop, so those cards now link to what they cost in milliseconds.
- ✅ **Component math reconciled with the calculator.** Two real inconsistencies.
  Redis assumed 5 µs per command (~194k ops/s at 512 B) — above the top of the
  published unpipelined range; it now uses the calculator's 10 µs, which
  `redis-benchmark`'s 72k–180k supports. Postgres modelled no fsync wall at all, so a
  96-core box implied 80k TPS on CPU alone; it now carries a **commit durability**
  meter derived exactly as the calculator does (8 commits per fsync ÷ 300 µs ≈
  27k/s) — the ceiling cores cannot buy past, because a commit waits on the disk, not
  the CPU. Kafka's "~10 MB/s per partition" is relabelled as the operational
  guideline it is (recovery and rebalance time), not a disk limit: a partition is a
  sequential append and the disk streams GB/s.
- ✅ **`scalelab-design` skill** (`.claude/skills/scalelab-design/`) — codifies the
  hard-won UI/animation patterns (validated palette, label shrink-to-fit, edge-port +
  waypoint routing, runbook/tile/meter/trace styles, nine-chapter template + wiring
  checklist). The "nothing overlaps a label" invariant is now *enforced*: a dev-mode
  trace lint (`src/components/traceLint.ts`) console-warns any particle route that
  cuts through a node, any overlapping/off-canvas node, or unknown ids.

## App simulations (gallery)

- ✅ Social Feed (`/sims/feed`) — local → global, fan-out, hot keys, sharding.
  Reworked as a **guided mission lab**: capped/centered topology, per-stage goal
  checklists that latch as you trigger each lesson, KPI strip, bottleneck auto-tag,
  and an honest latency model (queue+service only — travel animation no longer
  counted, which had been drowning the queueing signal).
- ✅ Observability at Scale (`/sims/observability`) — logs/metrics/traces pipeline as a
  mission lab: single box → Kafka buffer → scale the index tier → **cardinality explosion**
  (the wall horizontal scaling can't climb) → hot/cold storage tiering with a live cost
  estimate → federate + per-team quotas. Reuses the Feed engine with observability hooks
  (cardinality inflates index/query cost; clusters multiply index capacity). Pairs with a
  planned **ClickHouse** flagship deep-dive (the storage box's spec sheet).
- E-commerce checkout — inventory contention, flash sales, sagas.
- Food delivery (FTGO) — choreographed multi-service sagas.
- Chat / messaging — websockets, connection scaling, ordering.
- Video streaming — transcode queue, CDN, object storage.

## New-domain components (paper-driven)

Cassandra · DynamoDB · Flink · etcd/Raft · ClickHouse · MotherDuck/DuckDB · Ray ·
Spark · inference engines (vLLM) · "Inside a web server" (concurrency models + TechEmpower).

## Ship it

- ✅ **Deployed — [systemscomic.com](https://systemscomic.com).** A static-assets
  Cloudflare **Worker**, not Pages: the "Connect to Git" flow now creates a Worker and
  runs `wrangler deploy`, which auto-detects Vite and refuses below v6 — so the answer
  was to state the deployment explicitly in `wrangler.jsonc` rather than chase a major
  upgrade for a plugin this site would not use. The SPA rewrite is
  `not_found_handling: "single-page-application"`, and it is the *only* fallback:
  a Pages-style `public/_redirects` with `/* /index.html 200` failed the deploy
  outright, because Workers validates that file server-side and correctly calls a
  catch-all rewriting to a path the catch-all also matches an infinite loop. Shipped
  alongside it: route-level code splitting, a 1200×630 OG card, `_headers` (immutable
  assets, revalidated index), README + MIT licence, and the repo renamed to
  `ddia-live-comic` — since renamed again to `systems-comic`, once it stopped being
  one book.
  Two lessons worth keeping. `wrangler deploy --dry-run` does **not** exercise
  server-side validation, so a config can pass locally and fail on deploy. And route
  splitting is a cascade hazard: lazy chunks changed stylesheet *order*, which flipped
  the winner between two rules of identical specificity and overlapped a table's text.
  All stylesheets are now imported from `main.tsx` in explicit order, theme last, and
  the overrides were rewritten to be order-independent.
- **Support / sponsor** — a Support section with a sponsor QR (GitHub Sponsors / Ko-fi).

---

## ★ North star (phase 3): the Topology Composer

**Idea.** A sandbox where users drag in infra components (web tier, LB, Redis, Postgres,
Kafka, S3, …), wire them together, define traffic, and watch their *own* architecture
scale and break. The deep-dives teach each block in isolation; the app sims show fixed
compositions; the composer is the synthesis — "build whatever you want and watch it break."

**Why it's the north star.** It's an *evolution of the Feed engine*, not a rewrite:
nodes-as-queues, particles, metrics, and the edge-port + waypoint routing are already
built. The component deep-dives are already the capacity "spec sheets" for each box.

**The hard part (design around this, don't fight it): traffic semantics.** A blank canvas
of boxes has no notion of what a "request" *does*. The make-or-break design decisions:

1. **Typed components with typed ports.** A web tier *emits* DB queries + cache ops +
   events; a DB *accepts* queries; a cache *accepts* ops and branches on hit/miss.
   Connections are type-validated, so "what flows" is well-defined and nonsense wiring
   is impossible.
2. **User-defined request flows.** The user clicks a path to define a request type
   (like our route arrays, authored in the UI). The existing engine handles the rest.
3. **Frame it as bottleneck-finding, not prediction.** "Push traffic, see which box
   reddens first, and what fixes it" stays honest with rough per-component math.
   "Predict your exact p99" is fragile queueing-network math — avoid promising it.
4. **Start from "fork a template," not blank canvas.** Let users open the Feed /
   e-commerce topology and modify it (insert a cache, add a replica, split a service).
   Lower risk, same thrill; blank canvas comes later.

**New work required:** the typed-port model, the flow editor, and auto-layout/routing for
arbitrary user graphs (elkjs / dagre for layout).

**Sequencing:** build this only *after* the component library is rich enough to be worth
composing and the design patterns are locked into the skill. Building it on a library of
three boxes wastes the idea. Until then: **make every new component a clean, typed,
self-describing module so it's "composer-ready" from day one.**

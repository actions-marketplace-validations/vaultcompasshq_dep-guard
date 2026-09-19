# dep-guard invariants

These are the cross-cutting rules the engine depends on. They are here
because every one of them was already true somewhere in the code and
written down nowhere both sides of a boundary could see it. This engine's
worst bugs have had the same shape, again and again: two pieces of code
each honouring a local invariant, neither aware of the other's. A
cohesion audit reads this file rather than re-deriving the list from
memory, and every new architectural decision appends to it.

Read this before changing the delta, the fingerprint, the path handling, or
anything that decides an exit code.

Derive, do not describe. This engine's defects keep landing in the same
place: a hand-maintained list of facts, kept alongside logic that lives in
another file, which has to stay in step with that logic and does not. `comparabilityKey`'s account of what the comparison rules read;
two diagnostics' copies of the tamper signal list; the pin-mismatch rule's
absence from the list of which walk feeds which rule; the claim below about
which values may enter a fingerprint. Every one of them was correct when it
was written and silently wrong afterwards, and every one failed in the
direction that lets an attacker through, because a stale description says
"nothing to see here" and a missing entry never announces itself. So when a
decision depends on what some other code does, compute it by running that
code and reading the result, or generate it from that code. If a parallel
list is genuinely unavoidable, make it the thing the logic is written
against, so an omission is a compile error rather than a silence.

This file records INTENT, and intent is not coverage. Every claim here
about what the engine already handles has to be checked against the code
before it is relied on: prose in this document has been wrong before, and
each time, the bug sat exactly where the prose waved a hand. A cohesion
audit that reads
this file as a statement of fact will confirm the gaps rather than find
them. Read it for what the engine is trying to do, then go and see.

## The fingerprint is a promise about facts, not about categories

A finding's fingerprint is a sha256 over exactly four things, in this
order: the rule id, the canonical package name, the manifest path, and
`details.signal`. Nothing else may enter it. Severity, the message, the
version, the corpus build date, and every other `details` key are excluded
on purpose, because all of them move under a review, a version bump, or a
corpus refresh without the underlying finding being a different fact, and a
fingerprint that shifted with them would silently invalidate every stored
baseline.

The signal is where the specificity lives, and it carries two distinct
duties. First, it separates findings one rule can raise about one
dependency at once: a tampered entry can lose its integrity hash, move
host, and downgrade its scheme simultaneously, and baselining one of those
must not silence the other two. Second, it must identify the *fact* and
not merely its category. Baselining a
benign migration to an internal registry used to accept every later repoint
of that package to any host, because both findings hashed the same
`host-changed`. So where a signal has a value-bearing subject, that value
belongs inside the signal string: `host-changed:https://artifactory.example`,
`pin-mismatch:registry.npmjs.org`. The four-component hash stays exactly as
specified; the fourth component just says something.

The test for whether a value may be folded into a signal is the stability
contract, not taste: it may go in only if it cannot move under a corpus
refresh or a version bump. A resolved host cannot, so it goes in.
Typosquat's matched target, matched rule, and target rank all can -- they
come from the shipped corpus -- so they stay out, and typosquat's slightly
coarse baselining is a deliberate consequence, not an oversight.

`local-source-changed` is the signal that rule caught out, and it is worth
naming because it looked like it obeyed the rule while breaking it. Its
subject is an origin, and an origin was already established as stable --
but a HOSTLESS origin is the path (see the tamper section below), and a
vendored tarball's path moves on every bump of it. Folding it in minted a
fresh fingerprint per bump that no baseline could ever absorb, which is
precisely what the stability contract exists to prevent. That signal is
therefore bare: `local-source-changed`, with both origins in `details`,
where nothing hashes them. The lesson generalises -- the question is never
"is this a value-bearing subject", it is "can this value move under a
version bump", and for a path the answer is always yes.

Renaming or splitting a rule id invalidates every baseline that mentions
it, so it waits for a major version.

## The delta has two walks, and neither is derivable from the other

`computeDelta` produces two independent lists, and the distinction is a
security property rather than an implementation detail.

`changes` is the manifest walk: which declared dependencies were added or
changed. It carries the specifier, the dependency section, the protocol,
and the manifest path, and it is what the name-based rules (existence,
typosquat, confusion's internal-name rule) and the specifier-based rules
(hygiene, tamper's git-source and url-source signals) need.

`lockEntryChanges` is the lockfile walk: which resolved entries differ from
the before lockfile, entry by entry, whether or not a manifest declares
them, and however many entries share one name. This is what the
resolution-based rules need -- tamper's integrity, host, scheme, tarball
and local source signals, install-script's flag acquisition, AND
confusion's pin-mismatch rule -- because in a real lockfile the
overwhelming majority of entries are transitive and no manifest names
them, and because one name can carry several entries, of which a single
"which version does this specifier resolve to" answer selects exactly one.

pin-mismatch was missing from that list for a while, in this file and in
the code both. It asks whether a RESOLUTION came from the host its scope
was pinned to, which is a resolution question wearing a name-shaped rule
id, and reading it off the manifest walk alone left it blind to exactly
the case it exists for: a transitive package under a scope pinned to a
private registry, quietly resolving from the public one. It reads both
walks now. Its sibling, the internal-name rule, stays on the manifest walk
and belongs there: it judges a name somebody declared, not a resolution.

Rules that judge a resolution must consume the second list. Rules that
judge a name or a specifier must consume the first. A rule that consumes
the first when it means the second is blind to transitive entries and to
any entry a decoy can hide behind, which is exactly how a repointed
transitive tarball and a same-version decoy both used to scan clean. A fact
reached by both walks is deduplicated on (manifest path, package name,
signal) for tamper and confusion, so a tampered direct dependency is
still one finding. install-script.ts dedupes on (manifest path, package
name) alone, without the signal -- deliberately, not an inconsistency.
The rule can raise four signals in total across its branches: 'added',
'flag-acquired', 'present' (raised instead of 'added'/'flag-acquired'
whenever hasComparisonBase is false, on either the npm or the pnpm
branch), and 'only-built-added' (the pnpm onlyBuiltDependencies branch's
own signal, pushed straight into `findings` rather than through this
dedupe at all). Only 'added' and 'flag-acquired' can ever co-occur under
one (manifest path, package name) key, though: hasComparisonBase is a
single value fixed for the whole scan, so within one run this dedupe's key
space sees either 'present' on every entry it covers or 'added'/
'flag-acquired' on every entry, never a mix of 'present' with either of
the other two -- and 'only-built-added' lives on the pnpm branch, which
this dedupe (guarding the npm branch's two loops) never runs for at all.
'added' and 'flag-acquired' are mutually exclusive outcomes of the same
acquisition question, never two simultaneous facts about the same
dependency the way tamper's signals can be, so there is nothing a third
component of the key would ever need to keep apart.

`kind` is `added` or `changed`, and never `removed`: dropping a dependency
cannot introduce any of the risks this tool looks for. Which checks gate on
`kind` is deliberate and worth stating, because getting it wrong is silent
in both directions. Existence and typosquat consider added dependencies and
aliases at any kind, since a retargeted alias has never been judged before.
Confusion's internal-name rule does the same; its pin-mismatch rule ignores
`kind` entirely, because a resolution that stopped matching its pin is
exactly as serious when no manifest line moved. Install-script treats
`added` and `flag-acquired` as different signals but reports both, and
never reports a bump that leaves an already-true flag true. Tamper ignores
`kind` for every signal: the git-source swap in particular almost always
arrives as a changed specifier, never as a new dependency.

## Pairing two lockfiles is a chain of guesses, and each guess owes a diagnostic

`selectEntry` picks which of a name's entries a specifier resolves to, and
has always said so when it could not tell. `pickCounterpart` answers the
other half of the same question -- which earlier entry a changed one
should be compared against -- and for a long time said nothing at all: it
fell through to whichever entry the lockfile happened to list first and
then let the checks assert a change against it. Two entries under one name
are ordinary (a mirrored older copy nested under another package, a second
version for a different peer set), so that positional pick turned routine
bumps into criticals whose message was backwards and which vanished if the
two lockfile keys were swapped.

Both selectors are therefore guesses under the same rule. A counterpart is
narrowed from the strongest evidence down: a matching version, then an
identical resolved URL, then a shared origin, then a matching
install-script flag, and each step only applies when it leaves a candidate
standing. The version rung is the one exception to "only applies when it
leaves a candidate standing": it is the only rung that runs unconditionally
(whenever the after entry has a version at all) rather than being gated on
more than one candidate still being in play, so it is the one rung that can
decide a pairing entirely on its own, with nothing else in the ladder ever
getting a look at the remaining candidates. That matters beyond ordering --
see "The narrowing ladder is the list that is still a description" below
for the attacker-constructible edge this creates when a before side holds
one hashed entry at one version and one hashless entry at another. A
pairing that survives all of that with more than one candidate is a guess,
and a guess may not manufacture a fact.

What a guess costs, though, is narrower than it looks, and getting that
wrong made the suppression attacker-constructible. Suppressing every
comparison signal for a guessed pairing was a defensible-sounding rule with
a hole in it: any name carrying two before entries -- which nested
duplicates make ubiquitous in a real lockfile -- could be repointed to any
host in one move by giving the evil entry a version no candidate shares.
Every narrowing step then fails, every signal goes quiet, and the scan
exits 0 with a note. The mistake was treating the VERDICT as the guess. It
usually is not: an entry resolving from a host none of the candidates ever
resolved from has moved whichever one it succeeds. What the guess really
costs is the before-value a message would print.

So the rule is: compare against every surviving candidate, and report a
signal every one of them produces, worded in terms of what is certain --
"not where any of the N earlier entries resolved from", never one
candidate's origin, and `details.counterpartCandidates` in place of ANY
before-side value. That means `details.beforeOrigin`, and it means
`tarball-repointed`'s `details.beforePath` too, which carried the first
candidate's tarball path for a while: no credential is in a pathname, but a
value read off one candidate is a fact about which candidate the delta
guessed at, and printing it as though the lockfile said so is the same
defect wearing a smaller consequence. Suppress only a signal that some candidates produce
and others do not, because that one really would be a fact about which
candidate was picked. Install-script follows the same rule: an acquisition
when no candidate ran scripts, silence when one of them did.

`delta-ambiguous-lock-entry` has three producers, and they mean different
things under the same code. `selectEntry` (delta.ts) raises it directly,
in `computeDelta`, on a pure SELECTION guess -- a dependency's specifier
matches more than one lock entry under its name and the code cannot tell
which one it resolves to -- with no comparison involved at all. That guess
is not reported unconditionally: computeDelta drops it when the specifier
held and the selected before/after entries do not differ (delta.ts:576-587),
unless `ambiguity.material === true` -- a merely version-level ambiguity
under a package nobody touched is noise, but one that could have decided
whether a tampered entry or a clean one was compared has to survive the
skip (the whole point of `pickCounterpart` below is a second, separate
guess about which BEFORE entry to compare against, and the two are not the
same event). The second producer, `checks/tamper.ts`'s `certainFindings`,
follows the suppression rather than the guess: it is raised only when a
comparison actually dropped something, and not otherwise -- which is what
makes IT mean something on its own terms. Firing that one on every guess
made it simultaneously the only honesty channel covering this hole and the
noisiest note in the set, since a nested duplicate of any bumped package
produces an undecidable pairing on nearly every routine refresh. The third
producer is `checks/install-script.ts`: it declares the same code
(`AMBIGUOUS_LOCK_ENTRY_CODE`, install-script.ts:31) and raises it from
`noteSuppressedByPairing` (install-script.ts:141), reached from
`agreementAcrossCandidates` dropping a verdict (install-script.ts:258) --
the install-script rule's own suppressed-acquisition case, following the
same follow-the-suppression rule as tamper's producer rather than the pure
selection guess above.

How that is decided is the part worth stating carefully, because the first
answer to it was wrong in the way this file is most concerned with. The
delta used to predict it: `comparabilityKey` listed the FACTS the
comparison rules read -- origin, hash presence, hash equality, version,
URL, install-script flag -- and two candidates sharing that key were
declared indistinguishable, so no note was raised. The list was not a copy
of the rules, only a description of them, and a description drifts the
moment a rule reads something it does not mention. Its failure mode is
silent and one-directional. A partially migrated lockfile holding a package
at `sha512-clean` beside a nested duplicate at the same version and the same
URL still carrying `sha1-old` gave both candidates the same key -- same
origin, same version, same URL, both "not the new hash" -- while the
algorithm ladder read a rewritten `sha512` as a forgery against one and as a
routine `sha1`-to-`sha512` rehash against the other. The critical was
dropped for disagreement, the key saw nothing to disagree about, and the
scan exited 0 with no findings and no diagnostics: attacker-benefiting
silence inside the mechanism built to end it.

So the decision is DERIVED, not described. The delta hands over every
surviving candidate (`beforeCandidates`) and says nothing about what a
comparison will make of them. Each check runs its real comparison once per
candidate, intersects the RESULTS, and raises `delta-ambiguous-lock-entry`
itself for anything the intersection dropped -- `certainFindings` in
`checks/tamper.ts`, and the acquisition suppression in
`checks/install-script.ts`. The drop and the announcement are one event, so
they cannot drift apart, and a rule that starts reading a new fact needs no
bookkeeping anywhere: the new fact changes the results, and the results are
what is compared. The invariant is therefore structural rather than
maintained -- a finding any candidate produces is either reported, when they
all agree, or announced as ambiguous. Neither silence nor a note about a
guess that cost nothing is reachable.

Do not reintroduce a key that describes these rules from outside them.
This engine's defects keep landing in a hand-maintained parallel list that
has to stay in step with logic living somewhere else, and this was
another one. If a derived key is ever wanted for speed, it has to be
generated from the comparison functions, not written alongside them.

The intersection has ONE implementation, in `checks/agreement.ts`, and both
checks that need it call it. That is not tidiness either. install-script
carried a hand-written approximation of it for a while --
`candidates.some(flagged)` plus a candidate count -- and the approximation
got a cell of the truth table wrong that the real intersection gets right
for free: when EVERY candidate already ran install scripts they all reach
the same verdict, so nothing is dropped and the scan can say plainly that
running one is not new. `some()` fires on "at least one", which is also true
when they all agree, so a bump of a scripted package beside a flagged nested
duplicate -- routine, and common -- announced an ambiguity with a false
message on every refresh. An imitation of a derived mechanism is a described
mechanism wearing the right words.

## What a dropped verdict costs, and what it must not cost

A dropped verdict is announced twice over, and the two channels do different
jobs. `delta-ambiguous-lock-entry` explains; it never touches the exit code,
because diagnostics never do. That left a real hole: a consumer reading only
the exit code saw a clean scan while some candidate had produced a CRITICAL.
So a drop whose set contains a critical ALSO produces a finding --
`lockfile-tamper`, signal `ambiguous-critical`, severity high, which blocks
at the default medium gate -- worded to say the engine could not determine
which earlier entry applies and the entry should be treated as suspect.

High rather than critical is the honest severity: a critical asserts the
tampering happened, and this cannot assert that. One escalation per
(manifest path, package name), however many verdicts went undecided across
however many lock entry changes under that name, because they are one
admission -- not one per undecidable entry, which is a level too fine:
`certainFindings` runs once per changed lock entry and could in principle
push more than one `ambiguous-critical` escalation for one package at one
manifest path, but `report()`'s own dedupe (manifest path, package name,
signal) collapses them, since the signal this escalation carries is the
constant `AMBIGUOUS_CRITICAL_SIGNAL` every time. The direction is the safe
one: a reader could in principle undercount how many entries went
undecided from a single admission, never overcount how many are suspect.
Drops carrying nothing above high stay diagnostic-only --
install-script's suppressed acquisition is the case, and making an
unattributable high block would put a note on every lockfile with a nested
duplicate back into the gate. The blocking decision stays in findings, where
it belongs; the diagnostic keeps its standing promise not to reach the exit
code.

## The narrowing ladder is the list that is still a description

`pickCounterpart`'s ladder -- version, then resolved URL, then origin, then
the install-script flag -- is the remaining described-not-derived list in
the engine. It decides which candidates
survive to be compared at all, and it is a hand-written account of what
distinguishes two entries rather than anything derived from the comparison
rules. It has not gone wrong yet. It is written down here because the
mechanism above only holds for the candidates the ladder hands it.

The bound below is recorded so the next maintainer re-tests it rather
than rediscovers it: a pairing the ladder narrows to a
SINGLE candidate is not a guess, so it announces nothing and escalates
nothing. That is reachable on purpose. It also means a before side holding
one hashed entry at one version and one hashless entry at another lets an
attacker's entry be steered to the hashless candidate -- match its version
and the first rung decides the pairing -- so `integrity-removed` never
arises, nothing is dropped, and there is nothing to announce.

That behaviour is deliberate and buys an attacker nothing they could not
get by editing the steered-to entry directly, which is why it is not
treated as a finding. It is nonetheless a real edge of the guarantee, and it
is load-bearing on the ladder staying as it is. ANY future change to the
comparison rules, or to the ladder itself, has to re-check this case
explicitly. Do not assume the derive-and-intersect mechanism above covers
it: that mechanism protects the comparison of surviving candidates, and this
is about which candidates survive.

The older half of this trade still stands where it applies: a critical
nobody can reproduce by reading the lockfile is how a gate loses its
reader.

Both selectors judge "same origin" through `resolution.ts`, which is also
what the tamper rules judge a move by. That is not tidiness: a second copy
of "same origin" would let the delta pair two entries the check then calls
different.

An added entry -- no before side at all -- is a third case, and it is not
judged. There is nothing to compare, so the comparison signals do not run,
and the entry is not held to an absolute standard either; an absolute rule
that would judge a new entry on its own merits is deferred. What is owed is
the admission, and in the delta modes it used to be missing entirely: a
fresh install scanned exactly like a scan that had evaluated every entry.
One aggregate `delta-new-lock-entries` diagnostic per scan names the count.
One, not one per entry -- a fresh install adds hundreds, and a per-entry
note would bury the diagnostics that name something specific. Audit mode
does not raise it, because `audit-no-tamper-comparison` already says the
same thing about the whole lockfile.

## A scan with no comparison base may report facts, never events

With no earlier revision behind the scan -- audit mode, or a staged scan of
a repository with no commit yet -- every dependency reads as added and
every install-script flag reads as newly acquired. Both are true of the
scan and false of the repository, and a check that spells them as events
files a blocking finding per flagged package on the first sweep of a real
repository, which is the sweep a new adopter runs first and abandons
fastest.

The delta carries `hasComparisonBase` so a check can tell the two
situations apart. install-script is the rule this bites: with a comparison
base it keeps its acquisition semantics, its `added` and `flag-acquired`
signals, and its blocking high. Without one, the same fact is reported as a
fact -- signal `present`, severity low, wording that says the package runs
an install script and that this scan cannot tell whether that is new. Low
sits under the default medium gate on purpose: knowing which dependencies
execute code at install time is most of why someone audits, so the finding
stays, and it stays out of the exit code. Any future rule that wants to say
"this is new" must consult the same flag rather than reading `kind`, which
in these modes says `added` about everything.

This is a rule about every reporting path, not about one of them, and it
holds however small the affected list is. pnpm's `onlyBuiltDependencies`
findings are the sibling case: `onlyBuiltDifference` reads the entire
allowlist as added when there is no before state, so `only-built-added` at
high said "newly added" about a list nobody had touched. It reports
`present` at low in that mode too, on the same wording pattern, and keeps
its acquisition signal and severity in the delta modes. That allowlist is
short enough that the false sentence could never have wrecked a sweep the
way the per-entry flag did; it was fixed anyway, because two paths
answering the same question differently is precisely the drift this file
exists to catch.

## What the tamper signals cover, and what the manifest walk cannot reach

The comparison-derived tamper signals are `integrity-removed`,
`integrity-changed`, `integrity-downgraded`, `tarball-repointed`,
`tarball-repointed-unverified`, `host-changed`, `scheme-downgrade`,
`local-source-changed`, and `resolution-unreadable`, and they are declared
once, in `tamper-signals.ts`.

A diagnostic that describes coverage lost across the board -- audit mode's
`audit-no-tamper-comparison`, the delta's `delta-new-lock-entries` -- names
them all, because naming a subset under-reports the engine's own blind spot,
which is the failure mode the whole diagnostic exists to prevent. This file
used to state that as a fact about every such diagnostic, and it was false:
both of those messages carried their own copy of the list, both copies were
written when there were six signals, and neither learned about
`tarball-repointed` or `resolution-unreadable` when those were added to the
check. Both messages are now built from the one declaration, and every
comparison-derived `details.signal` -- the nine named just above -- is
produced through a helper typed against that declaration, so one of THOSE
absent from the list does not compile and cannot go unnamed. Two signals
in `checks/tamper.ts` are deliberate exceptions, raw strings rather than
values from that typed helper, because they are not comparison-derived
signals at all: `AMBIGUOUS_CRITICAL_SIGNAL` (`ambiguous-critical`, tamper.ts
around line 682) names the dropped-verdict escalation described in "What a
dropped verdict costs" above, not one of the nine; and the git-source and
url-source signal (a template string, tamper.ts around line 720) is built
from the specifier's protocol and host, which are not fixed members of any
declared list to type against. Both are outside the "coverage lost across
the board" guarantee this paragraph is about, because neither is a
comparison signal that could go missing from a `tamper-signals.ts` update.

A diagnostic about ONE entry says which comparisons did not run for that
entry, which is a different and narrower sentence:
`tamper-resolution-unreadable` names the host, scheme and local-source
comparisons because those are the three that were skipped, while the
integrity branches still ran for it. Naming all nine there would be the
same misreport in the other direction.

`integrity-changed` closes what was a known gap: a hash removed was
critical, a hash rewritten in place was silent, and forging is strictly
worse than stripping. Registry tarballs are immutable, so one version
fetched from one URL has one hash forever; a different one is tampering or
a corrupt lockfile. It requires the version to be unchanged, which is what
keeps an ordinary bump out of it (version, URL and hash all move together
there), and it sits in an else-if with `integrity-removed` so a deleted
hash is reported once.

It used to require the resolved URL to be unchanged as well, and this file
defended that with the claim that a repoint "is already the more specific
`host-changed`". That claim was false, and the composition it hid is the
worst bug this engine has had. A repoint is only host-changed when the
ORIGIN changes. Within one origin -- lodash's resolution rewritten to
`https://registry.npmjs.org/evil/-/evil-1.0.0.tgz`, carrying evil's own
genuine hash, version untouched -- the integrity branch declined it for the
moved URL and the resolution comparison below dismissed it as a version's
tarball moving, so npm installed the attacker's bytes from the trusted host
and the scan emitted nothing at all. Not a finding, not a diagnostic.

`tarball-repointed` is that case: the version held, the origin held, the
URL and the hash moved together. One version has one tarball and one hash,
so this is a different artifact under the same name, and it is critical.
The algorithm ladder below deliberately does not run for it -- the ladder
forgives a rehash of the SAME bytes at the same URL, which this is not. The
one shape it must stay silent for is the ordinary bump, and the VERSION is
what tells them apart: when the version moved too, the URL and hash were
expected to move with it. An identical hash across the move also settles
it, in the other direction: same bytes, so the path change is a detail.

`tarball-repointed-unverified` is the hashless sibling of that case, and it
existed as a blind spot for the same compositional reason `tarball-repointed`
did. `tarball-repointed` requires an integrity hash on BOTH sides: a
differing hash is what proves the bytes changed. But the before side does
not always have one -- npm writes hashless entries for some resolutions, and
a partially hand-edited lockfile has them -- and when it does not, every
integrity branch is skipped (they all test `before.integrity !==
undefined`), while a same-origin path move clears host-changed,
scheme-downgrade and local-source-changed alike, exactly as it did before
`tarball-repointed` was added. So a held-version repoint to another tarball
on a host the project already trusts, on an entry that never carried a hash,
scanned clean. It fires now: same version, same origin, PATHNAME moved, both
sides a REGISTRY resolution, and no before integrity to have caught it. It is
reported at high, not critical, and the difference is the point -- there is
no differing hash asserting the bytes changed, only a path that moved under a
held version with no hash that could have verified it, so the severity does
not overclaim a certainty the evidence does not carry, the same honesty the
`ambiguous-critical` escalation keeps. High still blocks at the default
medium gate, because a same-version repoint on a trusted host is a genuine
supply-chain signal.

Two clauses of that gate are not obvious and both were wrong in the first
draft, so they are recorded here rather than left in the code.

The move is judged on the PATHNAME, never on the raw resolved URL string. A
raw-string comparison fires on things that are not a tarball move at all: a
rotated credential in the userinfo (`ci:OLD@` to `ci:NEW@` on a private
registry), a proxy's `?token=` query parameter cycling, a changed fragment.
All three leave the tarball exactly where it was, and each would have
produced a BLOCKING finding whose own reported `beforePath` and `afterPath`
were byte-identical -- precisely the self-contradicting output the
`host-changed` rule already refuses to produce for a scheme-only change.
Gating on the same `pathLabel` whose output the finding reports makes "the
two paths differ" true by construction. None of the three earns a diagnostic
either: the comparison ran and reached a verdict (nothing moved), so there is
no lost coverage to announce.

It is REGISTRY-only on both sides, and that clause is load-bearing rather
than tidy. A git-sourced resolution is hashless BY DESIGN, so a commit bump
under a held version satisfies every other precondition here. npm writes a
git dependency as `git+ssh://...#<sha>`, where the sha rides in the fragment
and the pathname never moves -- the pathname gate alone already excludes it.
pnpm writes a github dependency as a codeload tarball,
`https://codeload.github.com/o/r/tar.gz/<sha>`, where the sha rides in the
PATH, so the pathname genuinely moves and only this clause stops it. Without
it, every github-dependency commit bump would file a blocking high, on top of
the `git-source` finding the manifest walk already raises for the same
dependency, and it would quietly reverse `sourceSwapReport`'s deliberate
demotion of a pinned git source. A git source's integrity is git's own, and
judging it is `git-source`'s job. `resolutionKindOf` in `resolution.ts` is
where that classification lives -- the resolution-side counterpart of
manifest.ts's `Protocol`, kept there for the same reason `resolutionOf` is:
the lockfile walk has no manifest line to read a protocol off.

Its http(s)-forge host set holds exactly one entry, `codeload.github.com`,
and the two directions of error are NOT symmetric -- which is the part an
earlier version of this file got wrong. A host MISSING from the set
classifies as `registry`, and the worst that costs is a false positive on a
commit bump. A host wrongly IN the set classifies as `git`, which silently
removes a real registry from this signal's scope: that is lost coverage, and
it is silent. So an over-broad entry is the expensive mistake, and this file
previously blessed three of them. Bare `github.com`, `gitlab.com` and
`bitbucket.org` were listed and bought no coverage for either supported
lockfile format -- pnpm's github shape is codeload, and npm writes a `git+`
scheme for all of them, which the scheme set already catches -- while
`gitlab.com` actively cost some, because
`https://gitlab.com/api/v4/projects/<id>/packages/npm/<pkg>/-/...` is
GitLab's real npm package REGISTRY, so a hashless held-version repoint from
one project id to another produced no finding at all. The rule is to match
the archive SHAPE npm and pnpm actually write, never the domain of whoever
owns the forge; a forge domain looks like an obvious thing to add and the
reasoning that makes it wrong is not, which is why the mistake is recorded
here rather than quietly deleted.

The audit-mode exclusion is STRUCTURAL, not a guard, and the distinction
matters to anyone auditing this rule. Nothing here consults
`hasComparisonBase`. The branch lives inside `compare()`, which only ever runs
for a pair that HAS a before entry: `subjectOfChange` returns null without
one, and `candidatesOfLockEntry` returns an empty list. With no earlier
revision there is no before entry, so there is no move to compare and the
branch is unreachable, rather than reachable-and-suppressed. Any future
refactor that gives `compare()` a synthetic before side would reopen this,
and would need the flag consulted explicitly.

Its value-bearing subject is the origin (a host cannot move under a version
bump, so it obeys the fingerprint stability contract), and it is a distinct
signal string rather than a wider `tarball-repointed`, because a baseline
accepting one should not silently accept the other -- one is a hash-proven
different artifact and the other is an unverifiable move, two different
facts.

`resolution-unreadable` is the fail-closed case. A resolved URL the engine
cannot parse used to end the comparison with a bare return, and npm
genuinely writes such values (a bare relative path like
`vendor/payload.tgz`), so repointing an entry at one of them with the hash
rewritten to match was silent too. That broke two rules this file states
outright -- every guess owes a diagnostic, and a URL or hash the engine
cannot read must never be treated as one it approved. The package is now
named in a `tamper-resolution-unreadable` diagnostic whichever way it ends,
because the host, scheme and local-source comparisons genuinely did not run
for it; and when the resolution moved to or from something unreadable with
nothing vouching for the bytes, it is a critical. An identical hash on both
sides vouches for them, the same settlement `local-source-changed` makes.
The unreadable value itself never reaches the message or the details: a
string that failed URL parsing is exactly where a malformed credential
would survive the parsing that strips one everywhere else.

An integrity value is not an opaque string, though, and comparing two of
them without reading the algorithm prefix conflates three different events.
So a rewritten hash goes through a ladder, and the ladder -- not the branch
that reaches it -- decides which signal it is, or whether it is one:

- Same algorithm, different digest: `integrity-changed`, critical. This is
  the case with no innocent explanation.
- A stronger algorithm than before (sha1 to sha512, sha1 to sha384): a
  benign rehash, which is what migrating a lockfile off an older npm does
  to every entry it touches. No finding. Without this, a routine migration
  files a critical per dependency.
- A weaker algorithm than before (sha512 to sha1): `integrity-downgraded`,
  critical. This is the "removed or downgraded" half of the spec's rule
  said out loud -- an attacker who cannot forge a sha512 digest can try to
  get the lockfile to accept a weaker one instead.
- An algorithm either side does not recognize: reported as
  `integrity-changed`. Unknown is not weak and it is not benign; the
  comparison fails closed, because a hash the engine cannot read must never
  be treated as a hash it approved.

The strengths are an explicit ordered list, never a string comparison:
"sha1" sorts after "sha384" and before "sha512" lexically, which is two
wrong answers out of two. A value carrying several space-separated hashes
is worth its strongest one.

`local-source-changed` is the hostless counterpart of `host-changed`:
every `file:` URL has an empty host, so scheme-and-host comparison alone
left a vendored tarball swapped for a planted one completely silent, and
for such a resolution the path is the only thing that says which bytes.
That makes it fire on path moves, and two of those are ordinary work --
renaming a vendored tarball, moving the vendor directory -- so it now
requires that the integrity hash be absent, removed, or rewritten. An
identical hash on both sides proves the bytes did not move, which makes the
path change a reorg.

Its relationship to the `file:` protocol exemption is the part worth
writing down, because the two look like they contradict each other. The
manifest walk exempts `file:` (with workspace, catalog, link, and patch)
as internal wiring, so a dependency DECLARED as `file:../x.tgz` never
reaches this or any other registry-oriented rule. The exemption is about
declared specifiers; `local-source-changed` is about resolutions, and an
ordinary registry specifier can resolve to a hostless URL -- which is
exactly the swap being looked for. So the rule lives entirely on the
resolution side, and the lockfile walk is what carries it: for a
file-resolved entry the manifest walk either exempted the dependency or
never declared it in the first place.

The other two tamper signals, `git-source` and `url-source`, are the
mirror image and must be kept out of every lockfile gate. They read a
manifest specifier and nothing else. The whole check nonetheless sat behind
a "npm or pnpm only" early return, so a specifier rewritten to
`git+https://evil/...` reported nothing in a yarn, a bun, or a
lockfile-less repository -- against what the audit-mode diagnostic says in
as many words ("only the specifier-based git-source and url-source signals
ran") and what the yarn and bun loaders promise users ("lockfile-backed
checks fall back to manifest evidence"). The format gate belongs where the
resolution comparison begins, and nowhere above it.

Being specifier-only makes those two signals STATE signals, and both
halves of that word are load-bearing. They say what a dependency IS, never
that anything happened between two revisions, which has two consequences
the code now spells out where it used to get both wrong.

The first is severity, and the exact scope of the softening is the whole
point, because getting it one predicate too wide reopens the check's
headline attack.

A git source pinned to a full commit object id -- 40 hex characters for
sha1, 64 for the sha256 object format git is migrating to -- names bytes
that cannot change. One on a branch, a tag, an abbreviated SHA, or no ref
at all names bytes whoever controls the repository can replace under a
dependent with nothing in the manifest moving. Reporting both at one
unconditional critical hard-blocked the first commit of any repository
with a long-standing pinned git dependency, which is a legitimate
configuration, and the finding fires whether or not anything changed, so
there was no revision to get past it on.

The demotion that fixes that belongs to the STATE case alone: `low`
requires a full commit object id AND the absence of a comparison base.
A pin says the bytes cannot change FROM HERE. It says nothing about
whether moving to them was the change under review, and an attacker's
fork pinned to a commit is still an attacker's fork -- the pin makes it
more attractive, not less, because it looks deliberate and reviewed. A
first version of this fix read the pin off the specifier alone, and so
reported `"^4.17.21"` rewritten to `github:attacker/lodash#<40 hex>` at
low with exit 0: the precise shape this check's own header names as the
attack it exists for, converted into a note. With a comparison base every
branch here blocks, `added` as well as `changed`, because with a base
`added` means genuinely newly added and deserves the look; without one,
everything reads as added falsely, which is the situation the demotion
covers and the only one.

The mutable case keeps `critical` in both modes, deliberately and unlike
the `ambiguous-critical` escalation above: that one is softened to high
because it cannot assert its fact, whereas this one is certain -- the
dependency really does install whatever that ref points at today. The pin
is git-only: a url source names a tarball at a URL whose bytes can be
swapped however hex-shaped its fragment looks.

That makes three messages, not two, and the third is not decoration. A
pinned source in delta mode carries a blocking severity, so it must not
carry reassuring wording: a critical whose text says the commit "cannot
change under you" is the same self-contradiction the host-changed rule
avoids by naming full origins, and a reader told that the severity and the
text disagree believes the text. The low variant says instead that the
scan has no earlier revision and therefore cannot tell whether the pin is
new.

The second is `kind`. With no comparison base every dependency reads as
`added`, and a state signal spelling that as `added` told a first-time
adopter their years-old pinned dependency had just been introduced. These
two signals report `kind: 'present'` when `hasComparisonBase` is false, the
same word install-script uses in that mode; the comparison-derived signals
are genuine events and keep their own kind. This is the "may report facts,
never events" rule applied to the rule it bit second.

`present` is the state-signal value of `details.kind`, and it is the third
member of a set that is `added | changed` everywhere else in the engine.
`ReportedKind` in `checks/tamper.ts` declares it, and the expression that
produces it is annotated against that type, because `details` is a
`Record<string, unknown>` that would accept any string at all and a value
this contract-bearing should not rest on one un-checked template.
`ComparisonSubject.kind` stays `added | changed`: the comparison signals
describe events and must never acquire the third value.

None of that may touch `details.signal`. The severity, the message, the new
`commitPinned` detail and `kind` are all outside the fingerprint by design,
so a baseline recorded against one of these findings survives every one of
these changes. A test pins the literal sha256 that dep-guard 0.2.2 produced
for a real pinned git dependency, because folding the pin into the signal
string is exactly the tempting refactor that would silently invalidate
every such baseline.

## Path spellings have one source

Every path in a finding, a diagnostic, or a config match is anchored to the
git repository root and spelled the way `git-source.ts` produced it. It
resolves workspace directories by identity rather than by the spelling that
reached them, so a symlinked package directory is reported once, under its
real path, on both sides of a scan.

This matters far beyond tidiness, because three separate consumers key off
that spelling and none of them can tell a different spelling from a
different file. `ignorePaths` matches against it. The baseline matches
against it through the fingerprint, which hashes the manifest path. And the
two sides of a delta are paired by it -- if the git side and the working
tree side spell one package differently, every dependency of it reads as
removed from one path and added at the other. Anything that invents a path
of its own has to justify it against those three.

A finding the lockfile walk discovered is located IN THE LOCKFILE, and is
anchored there. It used to borrow the root manifest -- a file that has
nothing to do with a transitive entry -- on the reasoning that the root
manifest always exists. That reasoning ignored the three consumers above:
`ignorePaths: ["package.json"]`, a spelling `config-invalid` deliberately
allows so a monorepo can say it only cares about its workspace packages,
silently deleted every transitive tamper, install-script and pin-mismatch
finding in the repository. Anchoring them to the lockfile makes ignoring
them an explicit, comprehensible choice instead of a side effect, at the
cost of changing those fingerprints once -- cheap now, expensive after a
release. An entry a manifest DOES declare keeps that manifest, which is
also what lets a fact reached by both walks deduplicate into one finding.

Two fabricated anchors remain, both deliberate. `checkSingle` uses a
synthetic `package.json` for a question that has no file behind it, and
therefore skips both path-based filters, so that a repository's config for
an unrelated location cannot launder "is this name safe" into "clean". And
pnpm's workspace-wide `onlyBuiltDependencies` findings are anchored to the
root manifest, because the setting really is a property of the workspace
root and can live in that very file.

## A pnpm lockfile is a YAML stream, and which document is the project's is a rule, not a guess

`pnpm-lock.yaml` is not one YAML document. pnpm 12 self-manages the pnpm
binary and records that as its own document in the same file, separated by
a bare `---`, alongside the project's real lockfile. The parser used
`yaml`'s `parse()`, which throws `MULTIPLE_DOCS` on such a file, and the
throw arrived as `lockfile-parse` -- so every scan of a pnpm 12
repository was a could-not-run exit 2 that the umbrella turned into a
block on every commit, with no way around it. It reads the stream with
`yaml`'s streaming `Parser`/`Composer` now, capped.

The cap is a security property, not tidiness. A real pnpm 12 lockfile has
exactly two documents; anyone who can write the lockfile can instead make
it a stream of arbitrarily many, and a file of nothing but bare `---`
separators up to the 64 MB ceiling the git-diff path already imposes
composes one `Document` per separator and then materialises each with
`toJS()`, turning tens of megabytes into millions of Documents and array
entries before one is validated. So the stream is composed lazily and
fails closed the instant a document past the fourth appears -- four is
generous for a two-document format -- and nothing beyond the cap is ever
composed, nor anything materialised with `toJS()` until the whole stream is
known to be within the cap. `parseAllDocuments` is eager (it builds the
whole array before returning), which is why the streaming API is used
instead. The over-cap refusal is the same `lockfile-parse` throw every
other unreadable lockfile is, and its message names the cap. The
alias-bomb variant -- one document whose anchors expand combinatorially
under `toJS()` -- is bounded separately by `yaml`'s `maxAliasCount`, which
defaults to 100 (confirmed in yaml 2.9.0) and throws once expansion
exceeds it; `toJS()` is called with no options, so that default applies.

Two more things about the streaming read are load-bearing and neither is
obvious. The composer, like `parseAllDocuments`, does not throw for a
malformed document the way `parse()` does: it collects the failures on each
`Document`'s own `errors` array and hands the document back regardless, so
an unread `errors` array would let a document that failed to compose arrive
as an ordinary empty mapping and satisfy every lockfile-backed check
against a tree nothing read. Every document's errors are checked, and any
of them is the same `lockfile-parse` throw a single-document failure has
always been. And every document in the stream must be a mapping, not merely
the one that gets selected, for the same reason: understanding half a file
is how a partial read gets reported as a whole one.

The selection rule, in this order, because the order is the whole trick:

1. A stream of one document IS the lockfile, whatever shape it has. A
   repository whose only dependency is pnpm itself has exactly one
   document and it is the self-management block.
2. Otherwise the self-management documents are discarded FIRST. A
   self-management document is recognised the way pnpm writes it: it has
   importers, every one of them carries a `packageManagerDependencies`
   block, and none of them declares `dependencies`, `devDependencies` or
   `optionalDependencies`. Both halves of that test are required --
   "carries `packageManagerDependencies`" alone would misfile a project
   document that records its own packageManager field, and "declares no
   dependencies" alone would misfile a genuinely empty project.
3. Among what is left, the project lockfile is the document whose
   importers carry the `.` (root project) importer.
4. Absent any `.` importer, it is the document with the most importers,
   and only where that maximum is unique.
5. Anything else -- no candidate document at all, two candidates each
   claiming `.`, a tie on importer count, no document carrying importers
   -- is a `lockfile-parse` failure whose message names the ambiguity.

Step 2 has to precede step 3, and the reason is the exact shape of a real
pnpm 12 file rather than tidiness: BOTH documents claim a `.` importer
there, because pnpm's self-managed binary is recorded as a dependency of
the root project in its own document. A rule that reached for `.` first
would call every such lockfile ambiguous and keep failing precisely the
scans this exists to fix. This is the standing trap for anyone
re-deriving the rule from the format description instead of from a file.

The self-management document's own packages are deliberately NOT scanned.
They are genuinely installed dependencies and reading them would be real
coverage, and it is deferred rather than bundled here so that the fix for
the exit-2 failure is not carrying a coverage change nobody asked for.
`pnpm-multi-document-lockfile` names how many documents the file held and
how many were not scanned, so the omission cannot read as a clean scan of
the whole file. Scanning both importer sets, attributed, is the open
follow-up.

That diagnostic counts every UNSELECTED document, and it says exactly
that rather than calling them self-management documents. Step 4 of the
rule can select on importer count alone, in which case a discarded
document was never classified as self-management at all, and a message
naming a cause its own number does not support is the failure these
diagnostics exist to prevent.

## Diagnostics never change the exit code

The exit code comes from findings and the `fail_on` threshold, and from
nothing else. A diagnostic is how the engine says "I looked at this and
could not judge it" or "this coverage did not run", and it is deliberately
not a finding, because inventing a finding for a package the engine cannot
name is how a gate becomes noise people learn to skip.

The obligation this creates runs the other way: any coverage the engine
cannot provide must produce a diagnostic rather than silence, because
silence is indistinguishable from a clean result. That is why a missing
lockfile, an unparsed lockfile format, a binary lockfile, pnpm's absent
install-script flag, audit mode's unreachable tamper comparisons,
`checkSingle`'s reduced coverage, an unparseable npmrc pin, an unreadable
resolved URL, an ambiguous lock entry selection, an unmatched ignore entry,
a workspace directory the walk could not read, a resolved path escaping
the repository root, a symlink chain that cycles back on itself, and
findings dropped by a matched one all have codes. Adding a code is the cheapest possible fix for
a gap, and a gap with no code is a bug even when the code that has the gap
is correct.

Current diagnostic codes: `audit-anchor-differs`,
`audit-no-tamper-comparison`, `check-single-name-only`,
`delta-ambiguous-lock-entry`, `delta-new-lock-entries`,
`ignore-path-dropped`,
`ignore-path-unmatched`, `lockfile-binary-skipped`,
`lockfile-format-manifest-only`, `lockfile-missing`,
`manifest-alias-empty`, `npm-lockfile-invalid-entry`, `npm-lockfile-v1`,
`npmrc-pin-unparseable`, `online-check-unreachable`,
`online-deadline-exceeded`,
`path-outside-root`, `pnpm-lockfile-invalid-entry`,
`pnpm-multi-document-lockfile`,
`pnpm-no-install-script-flag`, `symlink-cycle`,
`tamper-resolution-unreadable`, `workspace-dir-unreadable`,
`workspace-duplicate-directory`, `workspace-glob-unsupported`.

This list is hand-maintained, not compile-checked -- `Diagnostic.code` is
typed `string`, so a new code compiles and runs without ever being added
here. It has to be re-verified against the code (grep git-source.ts and
the checks for every string literal assigned to a diagnostic's `code`)
whenever a code is added, rather than trusted as current because it is
checked in.

## A suppressed decision is reported, allow among them, and every count prints even at zero

The three ways a user tells the gate to stand a finding down are the
baseline, `ignorePaths`, and an `allow` entry, and each is the user's own
earlier decision rather than the engine's silence. A report that omitted
them would be byte-identical to a scan that found nothing, which is the
exact footgun the separate `suppressed` and `ignored` counts already
close: `suppressed` is the baseline's specifically, `ignored` is
`ignorePaths`'s specifically, and collapsing either into the other re-hides
what it hid. `allowed` is the third of that family and obeys the same rule.
All three are printed even at zero -- in the text summary line, in the JSON
result object, and (a SARIF result being only ever an emitted finding, so a
cleared name has no result to attach to) on the SARIF run's `properties` --
because a decision that only shows up when it happens to be non-zero is a
decision a reader cannot audit for.

`allowed` counts distinct package NAMES an `allow` entry cleared this scan,
not the number of rules that would have fired for them: an allowed package
that trips several checks is one decision the user made, and `allowedNames`
carries those names so the count is attributable rather than a bare number.
The count is a new report field rather than folded into `suppressed`
on purpose -- the stability policy freezes an existing JSON field's
meaning, so widening `suppressed` to also mean "or allow" would be a
breaking change, while a new additive field is the minor-safe path and
keeps the three decisions three distinct numbers.

The recording is done by `allowClears` in `checks/allow.ts`, which every
check calls in place of the bare `isAllowed` predicate -- and it is called
at the FINDING point, past the condition that decides a finding, not at the
top of the loop over changes. That placement is the whole of what keeps the
count honest: it records a clearance only where a finding would otherwise
have been reported, never merely because an allow-listed name appeared as a
change. `hygiene` and `install-script` gate after their own would-be-finding
tests; `existence` records only past the corpus and internal-name gates,
and `typosquat` only past `matchName`, because a name that is corpus-known
or bears no resemblance was never going to be a finding, so allow-listing it
cleared nothing. The two candidate-fed checks record at their own emission
points rather than in the shared `newRegistryNames` builder for exactly this
reason: the builder has not yet judged the name, so dropping (and recording)
an allowed name there would count a clean, corpus-known, correctly-pinned
dependency as a clearance that never happened. `confusion` runs both its
rules first and records once if either would have fired. This also cannot
broaden which rules `allow` covers -- it changes nothing about the dropping,
`lockfile-tamper` is still not subject to `allow` for the reason
`checks/allow.ts` states, and a rule that does not consult `allow` still
records nothing. A future check that silences a package by `allow` records
it for free by using `allowClears` at its finding point; one that calls it
before the finding condition, or reaches for `isAllowed` directly there, is
the over-count this placement exists to prevent.

## Failing closed, and the error codes that do it

Anything the engine cannot parse or trust stops the scan with a
`DepGuardError` carrying a code, because a security gate that passes on a
parse failure is how tampering hides. A malformed lockfile is not an empty
lockfile; a config file that is present but broken is not an absent one.

The codes, and what each one means:

- `config-invalid` -- a config file is present but unreadable, not JSON,
  not an object, carries an unknown key, or holds a value the gate cannot
  honour. Includes an `ignorePaths` entry that would match everything: a
  security gate does not get a quiet off switch, and dropping findings
  before the gate weighs them is one. "Everything" is any entry with no
  literal in it at all -- every character a wildcard or a separator, so
  `**`, `**/*` and `*/**` are all the same switch differently punctuated.
  A bare `package.json` is deliberately allowed: ignoring the root manifest
  names one file, and is how a monorepo says it only cares about its
  workspace packages.
- `baseline-invalid` -- the baseline file is present but not the shape a
  baseline has. Accepting a broken baseline would accept everything in it.
- `manifest-parse` -- a manifest is present and unparseable.
- `lockfile-parse` -- a lockfile is present and unparseable, including a
  lockfile that declares a format version whose required structure is
  missing, a multi-document pnpm lockfile whose documents leave the
  selection rule below no single project document to read, and a pnpm
  lockfile stream holding more documents than the parser will read before
  it fails closed (four; a real file has two). This case is a
  throw and not a diagnostic on purpose: falling
  back would leave the entries map empty and every lockfile-backed check
  silently satisfied.
- `corpus-missing`, `corpus-unreadable`, `corpus-corrupt` -- the shipped
  corpus is absent, damaged, or -- for `corpus-corrupt` specifically --
  valid but written in a shape this build refuses to trust: a
  `formatVersion` this build does not understand, a
  `walkComplete: false` (or anything other than the literal boolean
  `true`) from a walk that was stopped early or never finished, or a bloom
  filter whose bit-fill ratio is implausible (near 1, so it answers present
  for every name and silently disables unknown-package; or near 0, so it
  answers absent for every name). None of those is damage -- the file
  parses and the fields are the right types -- but this build cannot tell
  what it does not know, or must not serve a partial or fail-open result as
  if it were a complete one, so all are refused the same way a corrupt file
  would be. A corpus that reads as empty would flag every name, and a
  saturated one would bless every hallucinated name. See "The corpus format
  is versioned", "A partial corpus refuses itself", and "A bloom filter the
  reader cannot trust fails closed at load" below for the three checks this
  covers.
- `path-missing` -- the path to scan does not exist, or is not a directory.
  A path nobody looked at must not report a clean result.
- `read-error` -- a path exists but cannot be read.
- `git-error` -- git could not resolve what a delta mode needs, including a
  base ref that is not a usable ref.
- `name-invalid` -- `checkSingle` was asked about an empty name, which has
  no meaningful answer and must not be answered "safe".
- `severity-invalid` -- a finding or threshold carried a severity outside
  the known order. Unreachable today; it exists so that the day it becomes
  reachable, the scan stops instead of scoring the finding below every
  threshold and passing it.

Online checks are the one deliberate exception to failing closed: a network
problem degrades to the offline result with a diagnostic, and never blocks.

## Online checks degrade, and degrading has a precise meaning

The rule above is a sentence; this is what it obligates, now that it governs
a whole subsystem rather than one code path.

Degrading means the affected check contributes nothing it could not
establish offline, and nothing it did establish is taken away. The
one online step that removes a finding is described in "Standing a
finding down is a different act from suppressing one" below, and it is
an exception to the second half of that sentence rather than a
counter-example to it. The
typosquat popularity-asymmetry check either escalates a low-severity
resemblance match to high, when the network confirmed the candidate is
genuinely unpopular, or leaves it at the severity typosquatCheck already
gave it offline; a network failure means it leaves every candidate exactly
as it found them. The registered-squat check either adds a medium finding
for a recently-published, near-zero-download name, or adds nothing; a
network failure means it adds nothing, the same outcome as a scan that
turned up no candidates for it at all.

"Near-zero-download" includes a name the downloads API has no record for
at all, and that case is not an edge case for registered-squat: a
freshly-registered attacker name is exactly the name npm has no download
history for yet, so treating an absent count as "skip" made the check
structurally unable to fire on its own defining example. For
typosquat-asymmetry, the same absent-count case is a stronger version of
the low-download signal it already escalates on -- it is not specific to
a freshly-registered name the way registered-squat's purpose is; it
applies to any resemblance match the offline pass could not price.
`registry-client.ts`'s `fetchWeeklyDownloads` answers this with three
states, not two, and both checks read the distinction rather than
collapsing it: a name npm reports a real count for; a name npm's
response confirms it has no record for -- either a null entry in a
successful bulk response, or (a scoped name always, or an unscoped name
whenever it is alone in its 128-name batch of unscoped names) a
single-name 404 that a sentinel probe confirmed was genuine rather than
a symptom of a broken downloads API, by asking the same downloads
endpoint about a name certain to exist and certain to have downloads
(`react`, verified against the corpus's own popularity list) before
trusting the original 404 -- both checks treat this, and only this, as a
confirmed zero; and a name that is unresolved, which in practice a
single-name 404 no longer produces (it resolves via the sentinel probe,
or the whole fetch call throws and is diagnosed instead), so reaching
this state now means the fetch returned a malformed or unrecognized
response shape -- both checks
leave this one exactly as they would have before the distinction
existed, at the candidate's offline severity, never promoted to a
signal. Deliberately probing the downloads API rather than the registry
(fetchPackument) to confirm a single-name 404: those are two different
services with independent failure modes, and a downloads API that 404s
on everything while the registry is perfectly healthy would make every
existing scoped package read as a confirmed zero if the registry were
asked instead -- the same fabricated-block failure this whole
distinction exists to prevent, just moved to a different service.
Collapsing "confirmed no record" and "unresolved" into one absent-key
case, the way both checks did before this distinction was added, would
have let a broken downloadsApi silently mint a finding for every
single-name lookup instead of surfacing as online-check-unreachable --
the same failure mode a real network outage is supposed to produce, not
a wave of new findings.

Neither check downgrades a finding, removes one, or turns a network
problem into a reason to trust a name more than the offline checks
already do. Whatever a check could not establish is named, not implied:
a diagnostic with code `online-check-unreachable` says which check was
asking, how many findings or candidates were affected, and why the
request failed, so a consumer can tell three things apart, not two --
"the network was down" (a diagnostic fired), "the API answered and
confirmed nothing was on record" (now a signal, per above), and "the API
answered but this one name's status is unresolved" (silence, the same as
if the name had never been asked about) -- instead of reading any
silence as interchangeable with any other.

`enrichOnline` -- the function `scan()` and `checkSingle()` both call to run
the online checks -- must never itself throw. Each check it calls
(`applyTyposquatAsymmetry`, `findRegisteredSquats`) owns its own
try/catch around every network call it makes and turns a failure into a
diagnostic before returning, precisely so that `enrichOnline` never has
to. A network problem is routine, not exceptional, for this subsystem; if
it ever reached `scan()` as a thrown error, `--online` would turn a
pre-commit hook into something a flaky connection can block, which is the
one failure mode this whole feature exists to avoid.

The online cache (`online/cache.ts`) is deliberately not a trust input, and
that is a different property from failing closed rather than a relaxation
of it. `config.ts` and `baseline.ts` fail closed on a broken file because
trusting a corrupt one would accept whatever it happened to contain. A
stale or fabricated download count can swing a check in either direction
-- a forged high count can suppress an escalation the online checks would
otherwise have added, and (since the zero-download-blindness fix) a
forged low count, or a machine-global cache entry poisoned to a literal
0, can cause a check to fire, or escalate, for a package that is
genuinely fine; the cached 0 this fix writes for a confirmed no-record
answer persists for the same 24 hours as any other cached count and is
exactly as forgeable. What the online CACHE can never do, in either
direction, is remove or downgrade a finding the offline checks already
established. `applyTyposquatAsymmetry` only escalates a low to high or
leaves it alone, `findRegisteredSquats` only adds a finding or adds
nothing, and `resolveUnknownPackages` -- the one check whose answer CAN
lower a severity -- is deliberately not allowed to read this cache at
all. So a corrupt or forged online cache can cost an extra fetch, a
missed online-only escalation, or a spurious online-only finding, never a
name the offline checks flagged reading as clean.

That last exclusion is the load-bearing one and is easy to undo by
accident, so the reasoning is recorded here rather than left in a
comment. The cache holds `created:<name>` entries, written for
registered-squat's AGE question, and they never expire (CREATED_TTL_MS is
null, because a real creation date never changes). Serving
`resolveUnknownPackages` from them would be wrong twice over. A creation
date cannot answer the question that check actually asks -- it cannot
tell a real package from an npm security-holding placeholder or from a
name whose every version has been unpublished, which is the distinction
the whole check turns on. And because the entries never expire, a name
that existed when some earlier scan asked would read as present forever
afterwards on that machine, including a name npm has since REMOVED for
security reasons, which is exactly the case where a stale "it exists"
does the most damage.

The dominant removal path is npm's own security removal, not an author's
unpublish, and that is the reason this cannot be dismissed as rare. An
author-initiated unpublish is confined to npm's 72-hour window and is
genuinely uncommon; a security takedown has no window at all, happens
precisely to the malicious names this tool exists to catch, and happens
AFTER the name has been published long enough to be worth taking down --
which is to say, after the window in which a machine may well have
cached it. An earlier draft of this section argued the exposure was rare
by appealing to the unpublish window. That argument was wrong because it
was reasoning about the wrong removal path, and it is recorded here as a
mistake rather than quietly deleted, because the next person to think
about caching this answer will reach for the same argument.

So existence for the unknown-package downgrade goes to the network, or
the finding is left alone. Never to the cache. The cache remains exactly
as valid as it always was for registered-squat's age question, which is
what it was built for.

It is loaded permissively on purpose: a cache file
that fails to parse is discarded and rebuilt from an empty state, not a
`DepGuardError`.

## Online resolution may downgrade a finding, and may never remove one

`resolveUnknownPackages` (online/unknown-package.ts) is the only thing in
this engine that LOWERS a severity on the strength of a network answer.
It does not remove findings, and neither does anything else in the online
subsystem. The offline checks decide WHAT is reported; the network only
ever adjusts how loudly. That sentence is the invariant, and everything
below is why it is drawn there rather than one step further.

unknown-package asserts one specific thing: this name was not on the
registry when the corpus was walked. That assertion carries a stated
ambiguity in its own message -- hallucinated, or simply newer than the
corpus -- and it is the ambiguity, not the name, that makes the finding
decay. Every package published after a release's walk reads as unknown
to that release forever, so the false-positive rate on the flagship
BLOCKING check climbs continuously from the moment a release is cut, and
before 0.2.0 the only remedy a user had was an `allow` entry per
package: a permanent, rule-wide exemption bought to clear a finding that
was wrong about one fact.

A registry answer confirming the name exists contradicts that specific
assertion and nothing else. The finding is therefore DOWNGRADED to `low`,
which sits below the default `medium` gate, so the thing a user feels --
the commit is no longer blocked -- is delivered in full. It is not
removed.

An earlier version of this design removed it, on the reasoning that a
refuted claim should be withdrawn rather than merely quietened. The
reasoning was fine and the conclusion was wrong, because it conflated
"this finding should not block" with "this finding should not be
reported". Removing it makes "the corpus is stale about this package"
indistinguishable, in a JSON or SARIF report, from "there was nothing to
say about this package" -- and a reader auditing a report cannot then
tell a check that ran and cleared a name from a check that never ran at
all. Keeping the finding at `low` says both things at once: the gate is
satisfied, and here is what was actually established. It also keeps a
name a human may still want to look at in front of them, which matters
for the case in the next paragraph.

That case is the reason `low` and not silence, and it is a genuine gap in
coverage rather than a stylistic preference. A name REGISTERED after the
corpus walk but older than `REGISTERED_SQUAT_MAX_AGE_DAYS` falls through
registered-squat entirely -- that check only fires inside its age window
-- while also being absent from the corpus and now confirmed to exist by
the registry. For a name in that window, `--online` is NOT a superset of
offline coverage, and this downgraded `low` finding is the only signal
dep-guard emits about it at all. Removing the finding would close the
only channel that mentions it. Anyone tempted to drop these findings, or
to filter `low` out of a report by default, should read this paragraph
first.

The difference from suppression stays load-bearing. `allow`,
`ignorePaths` and the baseline suppress findings that remain TRUE; this
downgrades one whose specific claim was refuted, and it leaves every
other rule's verdict on that same package name completely untouched.
typosquat still reports the resemblance, registered-squat still prices
the name's age and downloads, install-script and tamper never enter into
it. "This name exists" and "this name is safe" are different sentences
and only the first one is ever being made here.

Four constraints follow, and none of them is optional:

- Nothing in this file removes a finding, on any branch. The function
  returns the same list it was handed. That is a property of the code
  rather than of any one branch, because a single branch that removed
  would be invisible in a test of the others, so there is a test that
  drives every reachable registry answer and asserts the list comes back
  the same length each time.
- A 200 is not by itself proof the package exists. npm keeps answering
  200 for a name whose every version has been unpublished, and for a name
  it has SEIZED after a malware or typosquat report and replaced with a
  `0.0.1-security` placeholder. The downgrade requires a real latest
  version, no unpublish record, and no security-holder marker; anything
  else leaves the finding untouched with its own reason recorded. The
  seized-name case is the one that matters most, because npm took that
  name over precisely BECAUSE it was malicious, and reading npm's seizure
  of a name as evidence the name is fine inverts the signal completely.
  The discriminator is computed once, in `registry-client.ts`, against
  the raw body -- a caller handed only `createdAt` cannot tell any of
  these apart, which is exactly how this bug got in.
- A 404 is not the mirror image of a 200 and must not be treated as one.
  It refutes the innocent half of the ambiguity instead of the guilty
  half, so it escalates to critical and rewrites the message to stop
  offering "published after that date" as an explanation the registry
  has just ruled out.
- Every other outcome -- a timeout, a 5xx, a malformed response, a spent
  per-run deadline -- leaves the finding exactly as the offline check
  made it. Not downgraded, not removed, not annotated into something
  weaker. A network that failed to answer is not an answer, and this is
  the one place where reading it as one would turn a blocking check off.

Neither the downgrade nor the escalation touches the fingerprint, and
neither can: the four hashed components are the rule id, the package
name, the manifest path and `details.signal`, and this function writes
only `details.onlineResolution` and `details.onlineResolutionReason`,
neither of which is hashed. A user who baselined an unknown-package
finding offline must not see it change identity the first time they pass
`--online`. Both directions have a test.

The existence question is asked LIVE and never served from the online
cache. See the online-cache section above for why: the cache holds
never-expiring creation dates written for a different question, and a
stale "it exists" is most harmful for exactly the names npm has since
removed.

## The online subsystem has one wall clock, and it is not the same as a request timeout

`registry-client.ts` bounds a REQUEST: two attempts, five seconds each,
plus whatever backoff cap the caller supplies. Nothing in that bounds a
RUN. A modest delta carrying twenty new names, each resolving in a
second or two, is a pre-commit hook that takes half a minute, and every
per-request budget involved is being honoured perfectly while it
happens. dep-guard runs per commit, so a latency budget that only holds
per request is not a latency budget.

`createOnlineDeadline` (online/deadline.ts) is therefore created once per
scan, in `enrichOnline`, and shared by every online step. A step asks it
before spending a request and stops when it is spent. What "stops" means
is fixed by the degrade rule above and is deliberately identical to what
a network failure means: the affected findings are left exactly as the
offline checks made them, nothing is removed, nothing is downgraded, and
the reason is recorded in an `online-deadline-exceeded` diagnostic rather
than implied by silence. A spent deadline can therefore only ever cost a
signal the scan would not have had offline either. It can never cost one
it already has.

The deadline is re-asked before every name in a per-name loop, not once
at the top of a step. A single slow lookup can spend the whole budget, so
a loop that legitimately started inside the budget can be outside it
three names later, and a step that only checked on entry would run the
remaining nineteen requests it had already decided to make. The two
places this matters are `resolveUnknownPackages` and
`findRegisteredSquats`'s packument loop.

`applyTyposquatAsymmetry` is gated from OUTSIDE, in `enrichOnline`,
rather than internally, and that asymmetry is deliberate rather than an
oversight: it issues exactly one bulk request and has no per-name loop,
so it has exactly one point at which it could stop, and that point is
before it starts. Adding a deadline parameter to it would be a second
copy of a decision with only one branch.

The order the three steps run in is a priority decision about how the
budget is spent, and it is written down because it looks arbitrary and is
not. unknown-package resolution runs FIRST because it is the only step
that can withdraw a false positive from the check that actually blocks,
and the only one whose absence gets steadily worse as a release ages away
from its corpus walk. The other two only ever add or escalate, so a
budget spent before them costs a signal that would not have existed
offline either; a budget spent before the first one leaves a user
holding a blocking finding they have no way to clear.

The budget is a constant (`DEFAULT_ONLINE_BUDGET_MS`, twenty seconds) and
not a config key today. If it ever becomes one, it becomes a config key
-- it does not become a second constant somewhere else that has to be
kept in step with this one.

## The popularity list is a trust input, and it is sized for its own rule

`scripts/data/top-packages.txt` is the list typosquat reads, and it is the
only corpus artifact that grants something rather than describing it. A
name in it is permanently exempt from being reported as a squat of
anything, so getting a name onto it buys immunity from the rule. Four
constraints follow, and none of them are conveniences.

- **Every name is verified twice, independently, before it is listed.** It
  has to exist in a walk of the registry this project performed itself, and
  npm's downloads API has to report it above the usage floor, measured at
  the time the list is built rather than claimed by whatever proposed it.
  Nothing is listed because a ranking said it was popular.
- **The floor is ten thousand downloads in the last week.** It is orders of
  magnitude above what a package with no adopters receives and cannot be
  reached by publishing alone, so clearing it means real installs. It is a
  bar and not a proof: counts can be bought, which is why the other three
  constraints exist.
- **No third-party fetch at build time.** The list is checked in, reviewed
  and diffed like source. A public ranking may nominate candidates, but it
  is vendored into the repository with its version and integrity recorded
  in the file header, read with a scanner rather than executed, and never
  pulled from someone's server while a corpus is being built. A
  supply-chain tool that fetches its own trust data from an unvetted source
  on every build is arguing against itself.
- **The list is sized for the rule that reads it.** Ten thousand names
  minimum. A short list does not fail loudly; it produces confident false
  positives, because a popular package that is absent is not exempt and so
  gets reported as a squat of whichever popular neighbour it resembles.
  This is not hypothetical: a five-hundred-name list reported micromatch as
  a squat of picomatch, npm-run-all2 of npm-run-all, and `@types/jsesc` of
  `@types/jest`.

Scoped names are the case that goes wrong quietly. npm's bulk downloads
endpoint refuses them, so they cost one request each where an unscoped name
costs a hundred and twenty eighth of one, and a list assembled without
noticing that ends up with no scoped names in it and no sign that anything
is missing. They are measured one at a time instead. The residual gap, that
a scoped package can only be listed if something nominated it, is written
into the candidates file header rather than left to be discovered.

The alias list is checked before this exemption, and `assertAliasKeysNotPopular`
is what keeps the two from contradicting each other. That guard now runs
against twenty thousand names rather than five hundred, so it is enforced in
the test suite as well as in the corpus build.

## The corpus format is versioned, and absence of the version is not the same as a wrong one

meta.json carries an optional `formatVersion` field, emitted as `1` by
`buildMeta` (scripts/lib/corpus-guards.mjs) from the first published corpus
onward and never before -- a format version cannot be assigned
retroactively once corpora exist in the wild, so nothing shipped before
this field existed can be given one after the fact. `assertMetaShape` in
packages/core/src/corpus.ts refuses to load a corpus whose `formatVersion`
is present and not one of `SUPPORTED_CORPUS_FORMAT_VERSIONS` (today, only
`1`), throwing `corpus-corrupt`: the corpus is not damaged, but its
declared format is not one this build knows how to read, and that is
exactly what `corpus-corrupt` covers (see "Failing closed" above).
docs/release/stability-policy.md promises a release reads its bundled
format and at least the immediately previous format version, so the day a
version 2 exists, `SUPPORTED_CORPUS_FORMAT_VERSIONS` has to grow to admit
both, not just move the comparison -- that promise is why the constant is
a list and not a single literal. The refusal message names the supported
versions by reading this same list (`.join(', ')`), rather than restating
them as a literal in the message text, so the two cannot drift apart the
day a second version is added.

`formatVersion` is ABSENT-tolerant on purpose: a corpus missing the field
entirely is accepted, not refused. That is the same "refuse only what is
explicitly wrong, tolerate absence" rule `walkComplete` follows (next
section) and for the same reason -- nothing has ever shipped, so a
meta.json written by a builder that predates this field (the committed
fixture corpus, and any corpus already built with a pre-versioning
dep-guard) is a legitimate local artifact missing the field, not a corpus
in the wild claiming an unsupported version. That is narrower than "every
meta.json anywhere": the current builder writes the field on every corpus
it produces now, and this suite's own tests build metas that carry it too
-- the tolerance is for what a pre-versioning builder could have already
produced, not a claim that nothing ever carries the field.

The reader's tolerance-of-absence is now safe to rely on, and the gate that
makes it safe is described in the next section. Before that gate existed, a
hand-built or otherwise malformed corpus with genuinely missing fields
would have loaded exactly as if it were a legitimate pre-versioning
artifact; the gate is what makes that scenario unreachable for anything
this project actually publishes.

## core and cli publish in lockstep, and a burned version is never re-released

`packages/core` and `packages/cli` always move to a new version together,
even when only one of them changed. `.github/workflows/release.yml`
asserts this before publish (see its "Decide the release kind, and refuse a
tag that is neither" step, which calls `scripts/classify-release-tag.mjs`)
and refuses to continue if they disagree. The lockstep check is the first
thing that script does, before it even looks at the tag, so a lockstep break
reports as a lockstep break rather than as a tag mismatch -- and it runs on
both kinds of release, an action-only tag included.

The reason is `pnpm`'s own publish behavior, not caution for its own
sake: `packages/cli/package.json` depends on core via `workspace:*`, and
`pnpm` rewrites that to an EXACT version pin -- not a range -- at pack
time, pinned to whatever core's version is at that moment. A cli
published without a matching core bump pins the OLD core, and a fix that
only touched core silently does not ship to anyone who installs cli at
its new version: npm resolves cli's dependency to the pinned old core
version regardless of what core's latest version is, and there is no
range for a later core patch to satisfy. Lockstep versioning is what
keeps that pin meaningful.

The corollary is that a version number, once published, is never
reused, broken or not: npm does not allow re-publishing an existing
version under any circumstance, so there is no version number a
corrective re-release could target even if this project wanted one. A
release that goes out broken is fixed by a new version, bumped in both
packages together, exactly like any other change -- not by finding a way
to overwrite the old one. See the comment on the publish loop's
already-on-registry skip in release.yml for the failure mode this
prevents: that skip exists to make a partial-release re-run safe, and it
must never be asked to make a corrective re-release of an existing
version look safe too, because there is no version left for it to target.

## A published corpus is built in the release job, never committed, and a release gate demands what the reader tolerates

`packages/core/data/corpus` (the path `DEFAULT_CORPUS_DIR` in scan.ts
resolves to when nothing overrides it) is gitignored on purpose: a built
corpus is about ten megabytes of generated data whose provenance is a dated
registry walk, and it belongs to a release, not a commit. Nothing is ever
checked in there.
Instead, `.github/workflows/release.yml`'s `release` job runs `node
scripts/build-corpus.mjs --out packages/core/data/corpus` as one of its own
steps, so every release builds its own corpus fresh from
`replicate.npmjs.com` and ships it inside the published tarball --
`packages/core/package.json`'s `files` array lists `data` alongside `dist`
for exactly this reason, and `scripts/tests/core-package-files.test.mjs`
guards against that entry ever being dropped again, since nothing else in
`pnpm test`'s suite would catch its removal. That test proves only that
the string `"data"` is present in the `"files"` array, though -- it cannot
prove npm actually packs the directory it names. The check that proves
that is `scripts/check-corpus-packed.mjs`, wired into release.yml right
after the shippability gate: it packs `packages/core` the same way the
publish step will (`npm pack --dry-run --json`) and reads the listing
back, so it is the one gate that actually observes the corpus reach a
tarball rather than inferring it from a string being present in a JSON
array. It is not part of `pnpm test` and does not run in CI outside a
release, which makes it easy to mistake for a redundant duplicate of the
test above and delete while tidying the workflow -- it is not: an agent
or reviewer who cannot picture how the two differ should re-read this
paragraph before removing either one.

That step has to run after `pnpm test`, never before, in the same job.
`packages/cli/tests/cli.test.ts`'s "a first run with no corpus built yet"
case asserts that a scan with no `--corpus-dir` and nothing at the default
corpus path fails with an actionable `corpus-missing` message -- the whole
test depends on that default path being empty when it runs. Building the
corpus first, at that same default path, would make the test's premise
false in CI the same way a local `corpus:build --out
packages/core/data/corpus` makes it false on a developer's machine. The
test now diagnoses that precondition itself (an explicit failure naming the
path, rather than the opaque `Expected: 2, Received: 0` it used to produce)
and release.yml's corpus-build step carries a comment pointing at this same
constraint, so reordering the steps for tidiness has to go through that
explanation first.

A corpus that is about to be published cannot lean on the same
pre-versioning-artifact excuse `assertMetaShape` extends to `formatVersion`
and `walkComplete` above -- nothing has shipped before this gate existed,
so there is no legitimate "written by an older builder" case for a corpus
this build is about to publish. `scripts/lib/shippable-corpus.mjs`
(`assertCorpusShippable`, run by `scripts/check-shippable-corpus.mjs` and
wired into release.yml right after the corpus-build step) is the release
gate that closes that gap: it refuses to publish unless all four corpus
files exist, `meta.formatVersion` is PRESENT and is one of
`SUPPORTED_CORPUS_FORMAT_VERSIONS` (imported from the built core, not
restated -- see "derive, do not describe" at the top of this file),
`meta.walkComplete` is PRESENT and is exactly the boolean `true`, the
walked-name floor and bloom-size cross-check below both hold, the
directory loads through the real `loadCorpus` with a known-popular name
(`react`) resolving as present in the bloom filter, and its bit-fill ratio
is plausible for a filter that actually received its claimed inserts. That
known-name check makes the gate additive to the reader's own checks rather
than a replacement for them: a corpus this gate accepts still has to load
the way a real scan would load it -- but it only catches a corrupted,
truncated, or substituted bloom filter, not an incomplete walk, because
`collectExtras` (scripts/build-corpus.mjs) injects every name on the top
list into the filter regardless of what the walk found, and `react` is on
that list; no other popular name would fare differently, since anything
popular enough to be worth probing is on the same list.

None of the checks below establish walk completeness on their own, and it
is worth being precise about what each one actually proves, because two of
them were mistaken for proof of completeness before and the gap that left
open is exactly what let a near-empty corpus pass every check but one.
`walkComplete` and `meta.nameCount` are self-reported: they are what the
builder claims about itself, and a hand-edited or stale `meta.json` can
claim anything. The bloom-size cross-check below pins `meta.json` against
`names.bloom` as they stood at build time -- it proves the two were not
edited out of step with each other AFTER the filter was written, which
rules out a mismatched hand-edit but says nothing about what was in the
filter when it was written. A filter created with the right geometry and
near-zero content -- a truncated or misread name store, with the walk
still self-reporting complete -- passes every check described so far. The
bit-fill-ratio check below the geometry check is what closes that: it
reads the bit array itself and asks whether roughly the claimed number of
names was actually inserted, which is the one thing in this list that is
physical evidence of content rather than a self-report or a consistency
check between two self-reports.

`meta.nameCount` does not clear a bare floor. It clears the floor MINUS
the names `top.json` and `aliases.json` inject into the filter regardless
of the walk -- the same union `collectExtras` computes, read directly from
the two files the corpus being gated ships, not recomputed from anywhere
else. A bare `nameCount >= floor` check could in principle be satisfied by
an inflated top list alone, with the walk itself contributing almost
nothing; subtracting the injected extras first closes that. The floor
itself is unchanged (`DEFAULT_MIN_NAME_COUNT`, one million, against a real
walk's several million names). This is still a check on the SELF-REPORTED
`nameCount`, though, not on the filter's actual contents -- see the
bit-fill-ratio check below for the one that reads the artifact itself.

`meta.json` is self-reported; `names.bloom` is a physical artifact on
disk. The gate asserts they agree: the expected serialized size for
`meta.nameCount` and `meta.fpRate` is derived by calling the real
`BloomFilter.create([], meta.nameCount, meta.fpRate).serialize().byteLength`
(imported from `packages/core/dist/bloom.js`, the same module
`scripts/build-corpus.mjs` uses) rather than restating the bit-array
sizing formula or the header layout as a second copy -- again "derive, do
not describe". `BloomFilter.create` sizes its bit array from the count and
fpRate it is given, never from what it actually inserts, so an empty
filter built with a corpus's own claimed values has exactly the geometry a
real one built with those same values would. Comparing that against
`names.bloom`'s actual on-disk byte count is what stops a hand-edited or
stale `meta.json` from claiming a walk that never happened: every field
in it can read as a plausible type while the physical filter never grew to
match, and only a comparison against the artifact itself catches that. It
proves meta and the filter agree; it does not prove either of them is
telling the truth about what was walked, because `BloomFilter.create`
sizes its bit array from `count` and `fpRate` alone and never from what is
actually inserted -- a filter built with a huge claimed count and a single
real insert has exactly the same on-disk size as one genuinely built from
a huge walk.

The bit-fill-ratio check (`assertBloomFillRatioPlausible` in
scripts/lib/shippable-corpus.mjs) is the physical check the two checks
above are not. A bloom filter sized the standard way (`m` and `k` chosen
from `n` and a target false-positive rate) has an expected bit-fill ratio,
after `n` real inserts, of `1 - e^(-kn/m)`, which the optimal
`k = (m/n) * ln(2)` that `BloomFilter.create` computes drives to almost
exactly 0.5, independent of `n` and of the target false-positive rate. A
filter that claims `n` but received only a handful of real inserts reads
nowhere near that -- fill approaches 0 as the real insert count falls far
below the claim. The gate reads `names.bloom` back through the real
`BloomFilter.deserialize` (not a reimplementation of the header layout
bloom.ts documents -- `bits` and `bitCount` are typed private in bloom.ts,
but TypeScript's `private` erases to a plain instance property in the
compiled output the gate imports, so they are genuinely reachable without
hand-parsing the header) and refuses anything outside `[0.25, 0.75]`,
generous margin around the ~0.5 expectation. This is the check that
answers the question the two above cannot: not "do meta and the filter
agree", but "does the filter actually hold what it claims to".

`scripts/tests/shippable-corpus.test.mjs` exercises both directions of
every rule, including the two cases the reader tolerates and this gate does
not (formatVersion absent, walkComplete absent) -- verified adversarially
by weakening the gate to match the reader's tolerance and confirming those
specific tests, and no others, go red -- and also covers `readMeta`'s two
failure branches directly (meta.json present but unreadable as a file, and
present and readable but not valid JSON), the walked-name floor's
extras-subtraction specifically (a nameCount that clears the bare floor
but is almost entirely injected extras, verified adversarially by
reverting the subtraction and confirming exactly that test goes red), and
the bloom-size cross-check in both directions, including the case the
check exists for: a `meta.nameCount` inflated far beyond what the
`names.bloom` on disk actually holds (verified adversarially by disabling
the cross-check and confirming exactly those tests go red).

The release smoke job (`smoke-published`) passes no `--corpus-dir` to any
of its four `dep-guard check` invocations, on purpose: the point of that
job is to prove the corpus that actually shipped inside the published
package resolves correctly at its default path, not to re-prove something
about the repository's own fixture corpus (which the job no longer checks
out at all). It asserts `react` resolves as known and that ALL THREE
distinct hallucinated names resolve as `unknown-package` findings --
three names, and requiring every one of them, because the corpus is
rebuilt on every release now, so a single name's non-collision against the
bloom filter's 0.0001 false-positive rate is a fresh draw each time
instead of a fact fixed against a committed fixture. Requiring all three
is the stronger check: a bloom filter that wrongly answered "present" for
roughly half of all inputs -- a plausible shape for a deserialization
regression -- would still pass a weaker "at least one" check 87.5% of the
time (it only fails when all three collide, which is down near 1e-12 at
the real rate), where requiring all three fails in that same scenario
87.5% of the time. What that costs is a higher spurious-failure rate
against a genuinely healthy corpus, roughly 3e-4 per release, from the
union of three independent ~0.0001 chances that any one collides -- well
within tolerance for a gate that runs once per release.

## A partial corpus refuses itself, and the builder has to verify around that refusal

`buildMeta` writes `walkComplete: false` when a build is stopped early
(`--max-names`, which `pnpm corpus:slice` uses) -- see
scripts/build-corpus.mjs. `assertMetaShape` refuses to load any corpus
whose `walkComplete` is present and not exactly the boolean `true`,
fail-closed on any other value (a stray string, number, or `null`, not
only an explicit `false`), throwing `corpus-corrupt`: a partial corpus
reports every name the walk never reached as unknown, which is dangerous
in production and useful only for testing the build pipeline itself, so
it must never serve a real scan. `buildMeta` itself now requires
`walkComplete` to be a real boolean before it will write one, for the same
reason -- the value entering a load-bearing field has to already be the
type the reader trusts, not something that merely compares loosely equal
to it.

That refusal is deliberately in the reader every scan goes through, which
means the builder's own post-write verification cannot route a partial
build through that same path -- `loadCorpus` would refuse the exact
artifact the builder just wrote on purpose, on every `--max-names` run,
including `corpus:slice`, and the artifacts would already be on disk with
the build's own resume hint unreachable. (This was exactly the shape of
the bug this section exists to prevent a repeat of: the first version of
these checks routed every build's own verification through the newly
strict loader with no exception, so `corpus:slice` broke itself the day
the loader got stricter.) The builder verifies a partial build's artifacts
directly instead (bloom membership and top-rank order, read straight off
the files just written), and only routes a complete build through
`loadCorpus` itself, which is the stronger check -- it proves the artifact
is what the scanner will actually accept, not just that the raw files are
well-formed. See `verifyBuiltCorpus` in scripts/lib/corpus-guards.mjs, and
its tests in scripts/tests/corpus-guards.test.mjs, which exercise both
branches against real on-disk artifacts and assert that `loadCorpus`
genuinely does refuse the partial one `verifyBuiltCorpus` accepts -- proof
the two paths are different, not just that neither happens to throw.

## A bloom filter the reader cannot trust fails closed at load

`BloomFilter.deserialize` validates the magic, the version, the geometry
(bitCount and hashCount both at least 1) and the byte length, and none of
those can see a filter that is saturated or empty: an all-ones bit array and
an all-zeros one both keep an intact header and the exact right length. A
saturated filter answers `has()` true for every name, so `hasName` is true
for every hallucinated name and the flagship unknown-package check is
silently disabled -- no finding, no diagnostic, the fail-open direction. An
all-zeros filter is the mirror: every name reads as unknown. Either is a
corpus this build cannot trust, so `loadCorpus` refuses it (`corpus-corrupt`)
via `assertBloomFillPlausible` in `packages/core/src/corpus.ts`, keyed on
`BloomFilter.fillRatio()`.

The check is in `loadBloom`, not `loadCorpus`'s eager section, so it stays
lazy the way the rest of the bloom load is (a scan that never calls
`hasName` never reads or validates the filter), and the validated filter is
cached only AFTER it clears the guard -- caching before would leave a bad
filter in the closure and every later `hasName` would answer from it without
re-checking, reopening the fail-open on the second call. The refusal lands
the first time `hasName` needs the filter, exactly like the existing
truncated-bloom case.

What this window is worth is narrower than its presence suggests, and
overstating it is the failure this paragraph exists to prevent. It is a
backstop against WHOLESALE degenerate shapes, not an anti-tamper control, and
a corpus that clears it is not thereby verified. Two facts fix that scope:

- Partial saturation passes. The false-accept rate of a filter at fill `f` is
  about `f^k`, so a filter well inside this window is already badly degraded.
  Measured on a 5000-name geometry: at fill 0.85 roughly 14 percent of
  hallucinated names are accepted at `k`=13 and 23 percent at `k`=10; at fill
  0.90, roughly 21 percent and 42 percent. Every one of those PASSES this
  window, and a corpus in that state would miss most of what
  unknown-package exists to catch while reporting nothing.
- A targeted insertion is invisible to any window. Setting the `k` bits for
  one specific name moves the ratio by `k/m` -- on the production filter
  (`k`=13, `m`=82,434,282) about 1.6e-7. No fill band of any width can see
  that; detecting it needs a signature over the artifact, which this is not.

So the window's job is only to refuse the all-ones and all-zeros shapes, and
its bounds are chosen to do that without false-rejecting a real corpus.
It is `[0.10, 0.90]`, deliberately WIDER than the release gate's
`[0.25, 0.75]` (`assertBloomFillRatioPlausible` in
scripts/lib/shippable-corpus.mjs). A bloom filter sized the way
`BloomFilter.create` sizes one has an expected fill of `1 - e^(-kn/m)` after
its `n` inserts, which the optimal `k` drives to almost exactly 0.5,
independent of `n` and of the false-positive rate -- so the release gate,
which only ever sees a full multi-million-name production corpus, can afford
the tighter band. The reader also serves the committed dev fixture (53
names, measured 0.5085) and, in tests and local development, one-name and
other tiny corpora. A tiny corpus's fill is a noisy single realization of
that 0.5 expectation, not the expectation itself: measured single-name
filters range about 0.25 to 0.70 across different names and fpRates, and the
ANALYTIC worst case is lower than any of those measurements -- for `n`=1 at
fpRate 0.0001 the geometry is `m`=20, `k`=14, and when the double-hashing
stride shares a factor with `m` the `k` probes collapse onto as few as 2
distinct bits, a fill of exactly 0.10. The earlier version of this section
quoted "0.25 to 0.667" as though it were a bound; it was two measurements,
and the analytic floor sits well below them, which is exactly the kind of
anecdote-as-fact this file warns about at the top.

So the release window would false-reject a legitimately small corpus at load,
and -- this is the part that rules out the more obvious design -- an
EXPECTED-fill band (observed against the fill implied by the claimed name
count) tight enough to be meaningful would too, because the variance is
larger than the drift of the expectation it would centre on.

The boundary is INCLUSIVE at both ends, and that is load-bearing rather than
incidental. The test is `fill < MIN || fill > MAX`, so a fill of exactly 0.10
and a fill of exactly 0.90 both PASS. At the low end that is required: the
analytic worst case for the smallest legitimate corpus is exactly 0.10, and
an exclusive bound would reject it. At the high end it is acceptable because
the shape being caught is exactly 1.0, a full 0.10 clear of the bound, and
because anything that ships has already been through the tighter release
band -- the load guard is the last net, not the first.

The production corpus fill quoted elsewhere in these notes (0.4904) was
measured against a local `.corpus-work` build. It is NOT reproducible from a
clone: `packages/core/data` is gitignored and empty in the repository, and
the shipped corpus is built fresh in the release job (see "A published
corpus is built in the release job"). Treat that figure as one observation
of one build, not as a checked-in fact a test could re-derive.

The window reads the physical bit array only (`fillRatio()` counts set bits
up to `bitCount`); it never consults the self-reported `meta.nameCount`,
which is exactly the field a corpus forged to justify a saturated filter
would inflate. This is why deriving an expected fill "for the claimed name
count" would be not only variance-fragile but a smaller trust surface than
reading the bits directly: an attacker who controls `meta.json` could set a
`nameCount` whose implied expected fill is near 1, and a saturated observed
fill would then match it. The physical-fill window has nothing for such a
lie to move.

This is additive to the release gate, never a replacement: the gate's
`[0.25, 0.75]` is tighter and still runs at publish, so it still catches
fills between 0.10 and 0.25 or between 0.75 and 0.90 that the load window
lets through. Because `assertCorpusShippable` reaches `loadCorpus().hasName`
(in `assertLoadsAndResolvesKnownName`) BEFORE its own
`assertBloomFillRatioPlausible`, a near-empty or saturated corpus now trips
the reader's guard first, with a message that also names the bit-fill ratio
-- the gate still refuses to ship it, just one check earlier.

This is a security hardening at the read boundary, a new refusal REASON at
load rather than a change to any verdict, signal, fingerprint, exit code, or
output shape. It fits the stability policy's patch case (a security defect
in dep-guard itself: a corpus that fails open was accepted), but it rides
the same release as the tamper-signal minor above, so it ships as part of
that minor.

## A control input is not read from the tree being judged (0.6.0)

There are exactly two kinds of file dep-guard reads from a repository, and
conflating them is what made a muting pull request work. A SUBJECT is what
is being judged: manifests and lockfiles. A CONTROL INPUT is what decides
how the judging goes: `.dep-guard.json`, `.dep-guard.local.json`,
`.dep-guard.baseline.json`, and `.npmrc`. Concretely the control surface is
`failOn`, `allow`, `ignorePaths`, `internalScopes`, `internalPrefixes`,
`extraAliases`, `online`, the baseline fingerprint list, and the `.npmrc`
scope-to-registry pins.

**The test for which kind a file is: does a rule READ it to decide whether
to fire, or does a rule JUDGE what is in it?** `.npmrc` fails that test in
the way that is easy to miss, and it was miscategorised here until a
reviewer caught it. Its dependency lines are nothing; its scope pins are
the entire precondition of the dependency-confusion pin-mismatch rule
(`checks/confusion.ts`, `pinMismatch`), which fires only for a scope that
HAS a pin. So a pull request that deleted `.npmrc` deleted the rule. That
was live and it was worse than silent: the run reported "no control input
changed in this pull request" while a control input had just been removed.
A file being repository content, and being read by `loadStates` alongside
the manifests, does not make it a subject.

Outside pull-request mode both kinds come from the same place, and that is
correct: a pre-commit hook and a direct CLI run on a developer's own
checkout are inside the trust boundary already. In pull-request mode
(`--trust-base <ref>`) the subject stays the head tree and every control
input comes from `<ref>`.

The rule generalises to any control input added later, but only the
ENFORCEMENT half generalises for free. A new config key is a control input
by default and is covered the moment it is read off the base-ref config,
because the whole config object comes from `<ref>`. The reporting half does
not: `describeConfigChange` in `trust-base.ts` enumerates keys by hand to
build its parenthetical, so a key added without touching that function will
be correctly IGNORED for the run but summarised as a bare `config changed
in this pull request` with nothing naming it. Adding a config key means
adding it there too.

The corpus is deliberately outside all of this: it is not a repository
file, and its own load-time fill-ratio guard is the backstop that covers
it.

Three consequences hold and are each pinned by a test:

- The head-side value is never silently obeyed. It is ignored, and the
  report says it was proposed. Where there is no base counterpart at all
  (first adoption) the run uses the DEFAULTS and says `config added`,
  rather than trusting the head because it is the only copy there is.
- Both sides of the base-versus-head comparison are read through git, never
  one through git and one off disk. `readFileSync` follows a symlink and
  `git show` does not, so a mixed pair compares a link's target text
  against the linked file's contents and reports a symlinked control input
  as unchanged. That is the first half of a two-step whose second half
  never shows the control path in its diff at all.
- Failing to read a control input is could-not-run, exit 2, never a
  fallback. That covers an unresolvable trust base, a trust base that IS
  the tree being judged (same commit, or a different commit with an
  identical tree, which is what a merge ref looks like), a base-side
  config or baseline that will not validate, and a base-side config,
  baseline or `.npmrc` that is not a regular file (a symlink or a gitlink
  at the ref). The last one is a misconfiguration on the protected branch
  rather than something the pull request did, and the message says so,
  but it is refused all the same: an `.npmrc` read through a link yields
  no pins, and no pins is the loosest possible setting, not the safest.
  Every one of those has a tempting quiet fallback and every one of those
  fallbacks is reachable by whoever opens the pull request.

The reason this is stated as an invariant rather than left to the
implementation: the hole was not one bug, it was one CATEGORY of bug
reproduced five times over five different config keys, plus `.npmrc` on top
of that, and the next control input will make seven unless the rule is
written down where someone adding one will read it.

### Known open, in this same category (0.6.0)

Three things sit in this category and are NOT closed. They are recorded
here rather than fixed because each fix has a cost that needs deciding
rather than assuming, and an unrecorded known-open is indistinguishable
from an oversight.

**Workspace-local names are read from the head.** `candidates.ts` skips any
name in `delta.workspaceLocalNames`, which `delta.ts` takes from the AFTER
state, so a pull request that adds a workspace package named after the
dependency it is introducing makes the existence check skip that name. The
fix is not simply to read the set from the base: a pull request that
legitimately adds a workspace package would then have its own new package
reported as an unknown dependency, which is a false positive on an
extremely ordinary change; a union of both sides is probably the right
shape, and that is a design decision rather than a patch.

There is no mitigating factor, and an earlier draft of this entry claimed
one. It said the attack required committing a whole package directory and
manifest under the chosen name, and that is false: `lockfiles/npm.ts` adds
the name to `workspaceLocalNames` from a lockfile entry carrying
`"link": true` and nothing else, and no code reads the directory to confirm
it exists. So the cost is three lines inside `package-lock.json`, in the
very file the pull request is already rewriting to add the dependency. That
makes this QUIETER than the `.npmrc` hole, not louder: no separate file is
touched, and the report affirms that no control input was proposed while
the finding is gone.

**Workspace globs are read from the head**, in `package.json`'s
`workspaces` and in `pnpm-workspace.yaml`. These decide which manifests are
DISCOVERED, so de-listing a directory hides its manifest from the scan
entirely. Reading them from the base has the mirror-image cost: a pull
request adding a new workspace package would have that package's manifest
go undiscovered, which hides the very thing the gate should be looking at.
Discovery inputs may need a different rule from control inputs, namely the
union of both sides rather than either one.

**The composite Action never passes `--base`**, so a CI run scans in audit
mode and the comparison-based lockfile-tamper signals (integrity-changed,
tarball-repointed, and the rest of the list in the `delta-new-lock-entries`
diagnostic) never evaluate. Pre-existing in 0.5.0 and not introduced by
pull-request mode; recorded here because the trust-boundary work is what
made the gap legible.

## The scanner is itself a control input, and comes from outside the tree

The section above draws the line between a SUBJECT and a CONTROL INPUT and
then lists the control inputs as files. That list was incomplete, and the
missing entry is the largest one: **the program doing the scanning**. A gate
that reads its config from the base branch and then runs a binary the head
chose has moved the decision, not removed it.

The Action used to run `npx --yes "@vaultcompass/dep-guard@${DG_VERSION}"`
with the checkout as its working directory. Two routes followed from that.
Both were exercised against real npm during the investigation, and **the
harness now pins the two attacks' outcomes**: `bench/action-install.mjs` runs
action.yml's own install and run steps against real npm and two local,
ephemeral-port registries (no network),
once for this worktree's current `action.yml` and once for the pre-fix
`action.yml` read out of the `v0.6.0` tag, across three checkout shapes -- a
committed `.npmrc` alone, the scoped-key variant, and a planted `node_modules`
copy alongside it. The recorded result is `bench/baseline.action-install.json`;
`pnpm bench:action-install` compares a fresh run against it and exits non-zero
on any drift, and `pnpm bench:action-install:update-baseline` re-records it.
The v0.6.0 cases are the negative control: if they ever stop showing the
attack, the harness has stopped being able to see the thing it exists to
watch for, and `--compare` fails on that as loudly as on a regression in the
current action. The two routes it pins:

- **A committed `.npmrc` repoints the registry.** npx in non-global mode
  reads project config from its cwd, and `--yes` means no prompt. A pull
  request adding one root file chooses which registry the scanner is
  fetched from. Note that `.npmrc` was already on the control-input list
  for its scope pins; this is a second, sharper reason it belongs there.
- **An installed copy wins outright.** `npx pkg@version` run in a tree whose
  `node_modules` already satisfies that spec runs the local copy and never
  contacts the registry. The version pin degrades from a choice of program
  to a satisfaction check on a package the head wrote, and any workflow with
  an install step before the gate hands that over.

**The rule: install the scanner from the registry into a prefix under the
runner temp, start npm from the runner temp, and call the result by absolute
path.** Not "install outside and run wherever": a composite step with no
`working-directory` runs at the workspace root, so npm would still start
with the head's `.npmrc`, manifest and lockfile under its cwd. Global mode
is documented not to read project config, which is a property of a version
of npm rather than of this repository, and is not what the boundary should
rest on.

**The install also refuses to run the tree's scripts, and verifies what
arrived.** Two more properties of the same step, both following from the
scanner being a control input rather than an ordinary dependency.

`--ignore-scripts`, because the step runs on a runner holding the job's token.
Without it every package in the resolved tree gets arbitrary code execution
there on every run.

A ROOT MANIFEST under `<prefix>/lib`, and it is load-bearing. `npm audit
signatures` audits the tree's EDGES OUT, and a global install leaves that
directory with a `node_modules` and no manifest, so the root declares nothing
and the package just installed is on the far end of no edge. Without it the
audit covers the dependencies and SKIPS THE SCANNER, the one package it exists
for. Measured in the sibling repositories, where the gap is always exactly the
packages under check: vault-guard 13 installed and 12 audited without the file,
conductor 36 and 32. vault-guard shipped that bug once and recorded the short
count as evidence the check worked; this repository has the manifest from the
start.

WHAT THE VERIFICATION PROVES, narrowly, because the obvious summary is wrong.
It asks the registry for each name and version in the tree and checks the
signature served back. It does NOT read the installed files, so a tampered
install is invisible to it. It does NOT defeat a compromised registry, which
signs what it serves. And a MISSING attestation is not a failure, only a
missing or invalid signature is, so it does not require provenance despite this
package publishing it. What remains is that every name and version in the tree,
the scanner included, has to be one npmjs currently serves with a valid
signature.

KNOWN CONSEQUENCE OF FAILING CLOSED: a runner pointed at a mirror or proxy that
does not serve `/-/npm/v1/keys`, or a sigstore outage, installs fine and then
fails this step with `EMISSINGSIGNATUREKEY`.

**Enforced by:** the install cases in `scripts/tests/action-run-script.test.mjs`
(the argv carries the flag, the manifest names the version being installed, and
the audit is recorded). The stub is npm, so those prove the action ASKS; the
counts above are what a real npm does.

The install step's own `working-directory` line is DEFENCE IN DEPTH that
`bench/action-install.mjs` cannot observe directly, and that is worth stating
plainly rather than leaving a gap the harness's own coverage would seem to
close. `npm install -g` ignores project-level config regardless of its cwd,
so real npm behaves identically whether that step's `working-directory`
points at the runner temp or at the workspace root -- the real-npm harness has
nothing to compare, because there is no observable difference for it to
catch. It is the STUBBED suite, `scripts/tests/action-run-script.test.mjs`
("starts npm outside the checkout, so a committed `.npmrc` is never its cwd"),
whose stub records its own cwd and pins this particular line. The two suites
divide the claim rather than duplicate it: the stub proves where npm is told
to start; the real-npm harness proves what real npm does once it is asked to
run.

**The scan path passed to that binary must be ABSOLUTE, and the two halves
are inseparable.** Run from the runner temp with a relative `.`, dep-guard
resolves the runner temp as the repository, fails to resolve the trust base,
and exits 2 on every run, with a message telling the caller to fetch the
base branch with `fetch-depth: 0`, which they already did. A permanently red
required check explained by advice that cannot fix it. Ship both or neither.

**The version input takes an exact version only**, and defaults to the
SCANNER version the action tag shipped with, which is a different number from
the tag whenever an action-only release happens. A dist-tag hands the choice
of program to the registry on the morning of the run. A charset check is not
enough on its own: npm's specifier parser reads a value beginning with `.` or
ending in `.tgz` as a local path, so `.`, `..` and `payload.tgz` resolve
against a directory instead of the registry, and a value that is not valid
semver at all, such as `01.2.3` or `0.6.00`, falls back to being treated as a
dist-tag.

## On a pull request, `version` may not pin BACKWARD

The shape check above is a check on the FORM of the input and is not the
control for version choice: it admits every published version. On a same-repo
`pull_request` event GitHub runs the workflow file from the HEAD, so `version:`
is written by the pull request being judged. Once a second scanner version
exists, that is a bypass with an innocent shape: deleting a security step reads
as deleting a security step, while `version: 0.6.0` reads as version
management. Today it is shut only by coincidence, because exactly one scanner
has ever been published.

So on a pull-request event the step refuses a version BELOW the scanner this
action tag ships, and accepts anything at or above it. Pinning FORWARD stays
allowed, which is the direction the input exists for. That rests on an
ASSUMPTION the rule does not enforce: that a newer scanner is at least as
strict. Nothing bounds a forward pin, so a version ahead of the tag scanner is
accepted whatever its rules turn out to be.

Four properties, each load-bearing:

- `DG_TAG_SCANNER_*` is a constant of its own. It is not the npm floor in the
  install step, which is a property of the npm CLIENT and says nothing about
  the scanner, and it is not derived from the input. This repository has no
  flag-compatibility floor on the scanner, unlike vault-guard, where the two
  constants sit next to each other and mean different things; here the tag
  scanner is the only scanner-version constant in the file, so the check
  follows the version shape check directly.
- The comparison is against that hardcoded constant, never against anything
  derived from an input. `inputs.version` looks identical whether a consumer
  pinned the current version or the default supplied it, so the step cannot
  tell a pin from a default; the constant is the only source of truth. It is
  trustworthy because `action.yml` comes from the ref the consumer's workflow
  names, not from the pull request's tree. That holds when the consumer names
  this action by owner and ref; a LOCAL-PATH reference, the `./some/dir` form,
  reads `action.yml` out of the pull request's own tree, so the constant is
  author-controlled there and this rule protects nothing.
- The event test is `GITHUB_BASE_REF` being non-empty, the same one the run
  step uses to decide whether to pass `--trust-base` under `auto`, rather than
  a second detector to keep in step. It rests on a PLATFORM GUARANTEE worth
  recording, because a same-repo pull request's author writes the workflow file
  and the obvious bypass is therefore `env: GITHUB_BASE_REF: ""` at job level:
  GitHub documents that the default `GITHUB_*` and `RUNNER_*` variables cannot
  be overwritten and that such an assignment is ignored
  (https://docs.github.com/en/actions/reference/workflows-and-actions/variables).
- Written accept-only-if, not refuse-if, for the same reason as the npm floor:
  `[` returns 2 on a malformed comparison and an `if` reads 2 as false, so a
  refuse-if shape turns an arithmetic error into permission. The comparison is
  component by component and never textual, because `0.10.0` sorts below
  `0.7.0` as a string and above it as a version, so a lexicographic check would
  refuse the forward pin this rule deliberately leaves open.

**What this does NOT cover, stated because the obvious summary is wider than
the rule.** It closes pinning backward on a SAME-REPO pull request, and nothing
else.

- Not forks, and on forks the rule costs something rather than merely doing
  nothing. A fork's `pull_request` run uses the BASE repository's workflow
  file, so a fork author never writes the `version:` that judges them and there
  is no hole there to close. But `GITHUB_BASE_REF` IS set on a fork pull
  request, so the check fires anyway and judges the base repository's own
  trusted workflow file. Once a newer scanner ships, a maintainer's deliberate
  backward pin in that base workflow fails EVERY fork pull-request run: a pure
  false refusal, on a pin nobody untrusted wrote. The remedy is the same as for
  any consumer, which is to remove the `version:` input.
- Not a pull request that deletes the step, moves the `uses:` pin to an older
  action tag, or edits the job away. Those are workflow-file edits, and the
  control is branch protection with required review on `.github/workflows/**`.
  Nothing in `action.yml` can substitute for it.
- Not push events. The rule fires exactly where `GITHUB_BASE_REF` is set, which
  is `pull_request` and `pull_request_target`; push runs are out of scope. Read
  that as scope, not as safety: a push to an UNPROTECTED feature branch runs
  that branch's own workflow file, written by the same author, with
  `GITHUB_BASE_REF` empty, so it is as author-controlled as a pull request and
  the rule does not cover it.
- It costs consumers nothing today, because the tag scanner equals the only
  published version. It starts costing something the first time two versions
  exist.

**Enforced by:** the `pinning the scanner backward on a pull request` cases in
`scripts/tests/action-run-script.test.mjs`. Because the tag scanner equals the
only published scanner, no legal input lands below it, so the behavioural cases
drive the real step text with the tag-scanner constant advanced one minor
version, the action as it will be the day a 0.7.0 scanner ships, and assert the
replacement matched, so deleting the constant turns them red. Plus a drift case
tying `DG_TAG_SCANNER_*`, the `version` input's default and both
`packages/*/package.json` versions to one number; a case proving the shape
check answers first for a value that is not a version at all, so `latest` is
told it is a dist-tag rather than lectured about pull requests; and an ordering
case bounding the `GITHUB_BASE_REF` gate between the shape check and the flag
initialisation, at both ends, because the run step tests the same variable the
same way and the validate step tests it again further down.

## The action tag and the scanner version are two numbers, and both get bumped

0.6.1 was the first release where they came apart, and the release commit that
created the split broke this rule inside itself: the README's copy-paste
example still said `@v0.6.0` while the prose ten lines below told the reader
to move to `@v0.6.1`. The one block anybody actually copies was the one
handing them the pre-fix action. A reviewer caught it.

**The rule: when either number moves, grep for BOTH.** The places that carry
one or the other, as of 0.6.1:

- `action.yml`, the `version` input's `default:` (the scanner version)
- `action.yml`, the `DG_TAG_SCANNER_*` constants in the Validate inputs step
  (the scanner version). Added in 0.6.4 with the pull-request pin rule above.
  A constant left BEHIND a published scanner is the dangerous direction: it
  goes on admitting the very pin it exists to refuse, and it does it quietly.
  `scripts/tests/action-run-script.test.mjs` ties it to the `default:` and to
  both package versions, so this one cannot be forgotten in silence.
- `action.yml`, the `version` input's description, which names an example
- `README.md`, the `uses: vaultcompasshq/dep-guard@vX.Y.Z` example (the tag)
- `README.md`, the prose about which scanner a tag installs (both numbers)
- `CHANGELOG.md`, the release heading and any migration line naming a tag
- `package.json` and each `packages/*/package.json` (the scanner version)
- `bench/baseline.action-install.json`. Its top-level `scannerVersion` field
  is NOT itself what `--compare` checks: `compareRuns` walks each recorded
  case's `observed` object only, so a stale top-level value would sit there
  uncompared and unnoticed. What actually catches a scanner bump is inside
  the cases instead: the `current--*` cases' `installedScanner.version` (the
  version npm actually installed), and the two negative-control cases that
  reach the hostile registry (`npmrc-only` and `scoped-npmrc-only`, at the
  `v0.6.0` revision) whose `evilRegistry.paths` still name the hostile
  stand-in's tarball at its packed version -- the third negative-control
  case, `npmrc-and-planted-copy`, never contacts a registry at all, so it
  carries no version either way. `legitRegistry.paths` no longer carries the
  version at all: it is recorded as package identities rather than tarball
  filenames on purpose (see `bench/action-install.mjs`'s `packageNamePaths`),
  so an ordinary commander or yaml bump stops failing the compare for a
  reason unrelated to the scanner's own version. A scanner bump without a
  `pnpm bench:action-install:update-baseline` still leaves this baseline out
  of step with the number everywhere else on this list, and `--compare` still
  catches it, just through these per-case fields rather than through the
  field at the top of the file.

**The release workflow now knows both shapes, and the tag has to earn the
second one.** `.github/workflows/release.yml` used to assert that a pushed tag
read `v` plus the package version and fail otherwise, so the v0.6.1 tag push
went red before install, build or publish and got no Release page at all. Its
version step now calls `scripts/classify-release-tag.mjs` instead.

A tag equal to `v` plus the package version is a package release, and it
publishes and tests exactly as it always has -- with one addition: the script
reads `action.yml` on this path too, fails if it cannot read the `version`
input's default, and refuses the release when that default is not the version
being published. Publishing 0.7.0 under tag `v0.7.0` while the action that tag
ships still installs 0.6.0 is the same split as an action-only release, in the
one direction nobody chooses on purpose. That check is skipped when the package
version carries a prerelease, since `action.yml` refuses a prerelease pin
outright and no legal default could match it.

Any other tag is treated as an action-only release ONLY if all five of these
hold, and fails with a message naming the one that did not: the tag is `v` plus
exact semver (no prerelease, no build suffix, no leading zeros, the same shape
`action.yml` validates its `version` input against); it is strictly greater than
the package version by numeric ordering, so `v0.9.0` against packages at 0.10.0
is a mistake and not a forward move; `CHANGELOG.md` at the tagged commit carries
a `## [X.Y.Z]` heading for the tag version, which is what separates a release
somebody decided to make from a forgotten bump pushed as a tag, since every
other condition here is satisfied by that mistake; both
`@vaultcompass/dep-guard-core` and `@vaultcompass/dep-guard` are already on the
npm registry at exactly the package version; and `action.yml`'s `version`
default equals that same package version.

On the action-only path the run still installs, builds, typechecks, lints and
tests. It is tempting to skip those on the grounds that `ci.yml` already ran
them, but this workflow never learns that: the ancestry check proves the tagged
commit is an ANCESTOR of `main`, which every intermediate commit of a merged PR
branch also is without ever having had a CI run of its own. And an action-only
release's whole payload is `action.yml` plus docs, which is precisely what the
public-hygiene lint and the action suites cover. What it skips is what exists to
protect a publish that does not happen: the corpus walk and its checks, the
packed-tarball install gate, the npm upgrade for OIDC trusted publishing, and
the publish itself. It then cuts a Release whose body says nothing was
published.

The ancestry check -- the tagged commit must be on `main` -- applies to both
kinds, because an action-only tag still moves the ref people run in `uses:`.
Every workflow condition that reads the decision is spelled positively
(`== 'false'` for the publish-side steps, `== 'true'` for the action-only
Release body): an output that is empty or missing then skips publishing instead
of running it, which `!= 'true'` would not. The registry lookup runs from a
temp directory with an explicit `--registry`, so no `.npmrc` in THIS REPOSITORY
can decide what "already published" means. That is the whole claim: a
scope-specific line such as `@vaultcompass:registry=...` in a user-level or
runner-level `.npmrc` still outranks `--registry`, and nothing here reaches
that. The rules and the reasoning live in
`scripts/lib/release-kind.mjs`; `scripts/tests/release-kind.test.mjs` covers
them with the registry lookup injected, and also asserts the workflow's own
wiring: which steps are gated, and the exact ordered list of every step from
the decision step to the END of the release job, so a step inserted anywhere
after the decision -- including after tag resolution, where a second publish
would sit next to the Release that announces it -- fails the suite until
somebody says which side of the gate it belongs on. The same file reads the
real `action.yml` and the real `CHANGELOG.md`, so a moved default or a
reformatted heading goes red in the pull request that does it rather than at
tag time.

They are allowed to differ, and an action-only release is the normal reason:
nothing in the scanner changed, so publishing a new scanner purely to keep two
strings matching would burn a version through a one-way trusted-publisher
path. What is not allowed is a document telling a reader to pin one number
while an example next to it pins the other.

**What this does NOT cover**, and the comment in `action.yml` says so: a
pull request can edit the workflow file, because a `pull_request` run uses
the workflow as it is in the merge commit. Branch protection on the base
branch with review required for `.github/workflows/**` is the control for
that, and nothing the action does substitutes for it. The boundary here is
against the TREE choosing its own judge, which is a smaller and achievable
claim. The absolute binary path is likewise not total: the shim starts with
`#!/usr/bin/env node`, so the interpreter is still a PATH lookup that a
cooperating workflow can influence.

**Testing this needs a harness that derives each step's environment and
working directory from action.yml itself.** A harness with its own table of
variables, or its own idea of the cwd, asserts a property of the harness: a
review deleted the entire install step from a copy of `action.yml` and all
25 tests passed, and removing `working-directory` from a step passed too.
The suite now reads both from the file, and `DG_ACTION_FILE` points it at a
mutated copy so any of this can be made to fail on demand. Both action test
files honour that override; one of them not honouring it produced a green
run against a weakened file.

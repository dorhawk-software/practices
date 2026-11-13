# An identity, in iterations, through the whole app

How to give a product its identity, and how to carry it into every
screen. It is written to be followed step by step, by a person or a coding
agent. The rules for the drawing itself (outlines, stroke ends, type
sizes) are in [visual-craft.md](visual-craft.md).

The lessons come from three passes in one day (2026-11-11): Obálka (a
bland app, pushed far), Crake (a strong identity, polished) and tern (a
strong identity, first wrongly limited to its logo). Product details here
are labelled examples. The rules hold for any product.

The work runs in three iterations, each agreed with the product's owner
before the next starts:

1. **Establish the identity**: research, facts, one physical idea, its
   objects ([below](#iteration-1-establish-the-identity)).
2. **Redesign a few parts** toward it, show them, iterate until agreed
   ([below](#iteration-2-a-few-parts-shown-iterated-agreed)).
3. **Redesign the whole app** against the agreed spec, re-audit, iterate,
   polish ([below](#iteration-3-the-whole-app-re-audited-and-polished)).

## Identity first, before the first screen

**What.** Ideally the identity is researched before anything is built,
and the app is polished from its first screen. A redesign after the app
exists should not be needed. The research covers who the app is for, what
it does and for which process, what inspires it, and what the market
already looks like.

**Why.** All three passes of 2026-11-11 polished apps that already
shipped screens. Each one meant redrawing work that was already built and
tested. The owner: "in an ideal world, the polish after an app is already
done should NOT be necessary at all". Products differ too much for one
look: Shrike and Crake are different kinds of product, aimed at
different processes.

**Apply.** Before the first screen of a new product, write a one-page
identity brief:
1. **Audience.** Who uses it, how often, in what setting and light, with
   what at stake (their money, their mail, their network).
2. **The job and the process.** What the app does, step by step, from
   the user's side. The identity should fit this process, not a
   category.
3. **Inspiration.** The references the owner holds up, and why each one.
   Look at them before drawing.
4. **The market.** Five to ten products in the same space. Note the
   category's defaults, so you can avoid looking like all of them.
5. **The idea and its facts.** The physical idea (see the bar below), and
   the facts about it, gathered from real sources.
6. **Tone.** How serious the product must be, with one sentence on what
   would go too far.

Show the brief to the owner and agree on it. Then design the first
screens with it. For an existing product, write the brief first anyway:
it is iteration 1.

**Check.** The project has the brief, and the owner agreed to it before
the first designed screen.

## Get the facts right

**What.** When the identity borrows from the real world, draw the real
thing. Research what makes it recognisable, and keep those features as
the drawing gets simpler.

**Why.** Tern's logo was a stock bird icon. The pass redrew it from what
a tern really looks like: a black cap that runs into a long, sharp bill,
long narrow wings, and the forked tail, kept for the flying bird. The
owner "really loved" that it went for the facts. Obálka's printed-matter
objects (an envelope's window, a postmark, a stamp) worked for the same
reason: real postal objects people recognise.

**Apply.**
1. Look up the real thing in reliable sources: field guides, museum
   collections, real objects, photographs.
2. List its two or three identifying features: the ones someone would
   name first.
3. Keep those features at every size the mark ships at. Simplify
   everything else.
4. Check the drawing against a photograph, then at 16 px.

**Check.** The design doc names the identifying features and shows the
drawing at its smallest size with them still visible.

## The name and the mark read clean (a hard stop)

**What.** A name, its spelling and every mark built from it must not
read as a slur, an insult, profanity or a sexual or derogatory term, in
any way it can be read: as a whole, in any part a capital, a gap, a
swapped letter, a colour change, a line break, a crop or an icon makes
stand alone, and in slang, not only in dictionaries. Any such reading is
a hard stop: the mark isn't shown again, and the name and mark are
reworked before anything else ships.

**Why.** Dorhawk's Windows-app runner (2026-11-13), first named after a
bird. A capital letter in the middle of the name, and the egg that
replaced that letter in the wordmark, both set its first letters apart
as a derogatory slang word. Seven design rounds, two reviewers per round
and the designer all missed it, because each read the bird's name they
knew. The owner caught it: "this is a hard stop for me". The name was
already on dorhawk.software.

**Apply.**
1. Before a name is agreed, and again before any mark is drawn, list
   every way it can be cut: each prefix and suffix, each part a capital
   or a mark sets apart, each hyphen, line break and truncation (the
   first letters alone in a narrow sidebar), and the name with a letter
   replaced.
2. Read each part as a stranger would: a slang dictionary, a plain web
   search for the part alone, and in every language of the owner and the
   market (Czech, English and German for Dorhawk at least).
3. Read the drawn mark at every size, covering what you know: what does
   a stranger read first? A letter replaced by a picture leaves the rest
   as a word of its own.
4. If anything reads badly, stop: withdraw the mark from every board and
   page, tell the owner plainly, and propose names and marks that can't
   be cut that way. Don't soften it or argue it's unlikely.
5. Record the check in the identity brief: the cuts read, the sources,
   the date.

**Check.** The identity brief lists every cut of the name and mark, each
read clean, with sources. No part of the name stands alone as a word
unless that word was checked.

## Iteration 1: establish the identity

The identity brief above, then the two rules below: the bar, and how far
to push.

### The bar: serious, with one physical idea

**What.** An identity pass gives a product its own look and feel: drawn
icons, a material or a physical metaphor, considered buttons and sections,
and one or two signature motions. It stays serious. It is playful but never
gamified, because people trust these apps with their mail, money or
network.

**Why.** The owner judged three apps against two references: a sibling
app with a strong look, and the company website (an envelope, a cellophane
window). Next to them the apps "lacked identity". One proposal then went
too far: dates drawn as rubber stamps on a government mail app's inbox
rows. The owner called it "taking it too far". A serious product that
looks like a toy loses trust.

**Apply.**
1. Name the references the owner holds up, and look at them first.
2. Find the product's one physical idea in its own name or job. Examples:
   printed matter for a postal app (envelope, window, stamp, postmark); a
   line the product keeps to, for a VPN that routes traffic; a seabird
   that brings mail home, for a mail client.
3. List the objects that idea gives you. Give each object exactly one
   job. Example: the envelope's window shows who it's from; the postmark
   shows when it came.
4. Put identity into those few objects only, never into every piece of
   data. A date stays a date.
5. Test each idea against "would I trust this app with my bank's
   letters?". If not, cut it.

**Check.** You can name the idea in one sentence and list its objects,
each with its one job. No object appears without a job.

### Scale of change follows the identity; scope is always the whole app

**What.** Judge how much identity the product already has before you
propose anything. A bland product gets pushed far. A product with a
working identity keeps its look and tokens and gets precise polish, plus
one or two objects that grow out of what is already there. Either way,
you review every screen.

**Why.** Crake already had a strong look: a line along its left edge. The
pass kept the look and grew that line into a timeline with marks. The
owner praised it for "staying true to the product", with "merely very
good polishes". Tern also had a defined design, so the pass first redrew
only its bird (logo, icon, tray, two empty states). The owner called that
"very naive": a defined design can still be improved. The full review
then found real gaps. The identity was missing from the screens used most
often. Boxes were creeping in. One flow looked like another app. The
canvas had drifted from the code.

**Apply.**
1. Rate the product: bland, partial, or strong. Write one sentence on why.
2. Bland: propose a new idea and its objects (see the bar above).
3. Partial or strong: keep the palette, type, tokens and voice. Find what
   is already there that can carry more meaning. Grow one or two objects
   out of it.
4. In every case, run the whole process below on every screen. "Polish
   only" sets how big the changes are, not whether you look.
5. Finding nothing to change is a valid result. Skipping the look is not.

**Check.** The proposal states the rating and lists every screen that
was reviewed, with a verdict for each.

## Iteration 2: a few parts, shown, iterated, agreed

**What.** Apply the identity to a few parts first: the logo and the
screens that define the product. Show them to the owner, iterate, and
agree. The agreed parts become the spec for the rest of the app.

**Why.** This is how the three passes actually went: the identity, then
a few screens, shown and iterated until the owner agreed. A few parts
are enough to agree on the idea and the polished spec. They are not
enough to call the product done; that is iteration 3.

**Apply.**
1. Survey every screen and board first. Read each one's source, not only
   its picture. Note where the identity is strong, generic, or missing.
2. Run an independent critique of the whole surface before proposing:
   two isolated reviewers, one doing a design review and one running an
   automated detector. Neither sees the other's output.
3. Verify every factual claim in the critique against the code before you
   report it. Reviewers get facts wrong. On tern, a reviewer said three
   undo windows disagreed. They were one window caught at three moments.
   Another said a flow looked like another app. The app already framed
   it correctly; only the canvas lagged.
4. Draw two or three variants for each open choice, in place, with real
   context. Every variant carries the whole identity
   ([below](#every-variant-carries-the-identity)): a variant that differs
   only in layout is a wireframe, not an identity option. Real context means the real header, the real status bar, real
   copy, both themes. The owner judges spacing from it.
5. Recommend one variant per choice and say why in one line.
6. Ask with concrete options. Ask at most four questions at a time.
7. After the pick, remove the other variants and their labels from the
   canvas ([design-before-build.md](design-before-build.md)).
8. Polish the picked design: a second critique, then fixes, then look at
   it again.
9. Repeat steps 4 to 8 until the owner agrees the parts are right.
   Expect several rounds.

**Check.** Every choice on the canvas has exactly one design left. The
critique report and its verdicts are saved where the next pass can read
them.

### Every variant carries the identity

**What.** From the first round of iteration 2, every variant shown uses
the agreed identity in full. That means the drawn icon family, the
identity's colours and type, and the idea's objects, each doing its job.
Variants differ in how they carry the identity, never in whether they do.
A quiet reference means restraint, not absence.

**Why.** The Windows-app runner's brief (2026-11-13) named Apple's small
utilities and Things as references. Round one read "quiet" as plain:
system greys, a coloured dot, stock symbols, a numbered list. All three
parts had three variants, and none used the egg, the icons or the
colours. The owner: "it is so plain, where are some icons? … virtually
no identity at all". A whole round was lost. Things itself has its own
blue, icons, type and motion.

**Apply.**
1. Before drawing, list what each variant must carry: the icon family
   (two families in round one), the palette, the type, and which of the
   idea's objects appear in this part and with what job.
2. Read each reference for what makes it recognisable, not only for its
   calm. Write one line per reference: "Things: calm, and its own blue,
   checkbox and type."
3. Vary the treatment between variants: how much colour, which object
   leads, line or filled icons. Don't vary whether the identity is there.
4. Structure-only choices (what goes where) are settled first, as a
   wireframe that says so. Don't present them as identity options.
5. Run "Before you show anything" on round one too, step 6 above all.

**Check.** Cover the product's name: each variant is still recognisable
as this product, not as the platform's default template. Every icon on
it comes from the family. The handoff says which objects each variant
uses.

### The real things the product handles

**What.** When the product shows other people's things (apps, files,
services, accounts), the mocks show real ones: real app icons, real
names, real file types. Never a drawn stand-in for something that
exists. Each one is sourced and credited on the board.

**Why.** The Windows-app runner (2026-11-13) runs Windows apps. Five
rounds showed drawn stand-ins (a blue square for Enterprise Architect,
"ACME Accounting 2009"), though the Musts already said "never
stand-ins". The owner had to ask: "use actual app logos, i wanna see how
they are incorporated". The real icons raised the design questions the
stand-ins hid: Windows icons come in any shape and macOS jails them on a
grey tile; a black and white icon breaks a colour-matching rule; a red
one reads as an alarm.

**Apply.**
1. Pick the real things your users bring: the owner's own first (an
   app on their Mac, their CrossOver bottle), then common ones.
2. Source each one, best first: the owner's own copy (an icon extracted
   from the installed app), the maker's site, Wikimedia Commons. Treat a
   download as untrusted: its own folder, read it before you embed it
   (no scripts or outside references in an SVG), check it is the right
   asset (an app icon, not a wordmark).
3. Credit the sources on the board in one line, and say the artwork is
   its makers', shown only to design the presentation.
4. Where the identity derives anything from them (colours from an icon),
   write the rule down and show the edge cases: no colour, an alarm
   colour, an odd shape.
5. Never show a real maker's product failing without a real test. The
   failure state uses a made-up product, and the board says so.

**Check.** No drawn stand-in for anything that exists. Every real asset
has its source on the board.

## Iteration 3: the whole app, re-audited and polished

**What.** Only once iteration 2 is agreed, redesign the whole
application against that spec. Redraw everything that falls short. Show
it to the owner and take their tweaks. The pass is done when the whole
app matches the spec, not when the showcase screens do.

**Why.** The owner, after the three passes: the redesigned parts show
"the idea of how we want to take the product further". What must follow
is an audit of "the entire application, its all sections, clickity-
clacketies, modals, animations, processes", then iterating and
re-auditing until it is polished.

**Apply.**
1. Build an inventory from the code, not from the canvas or from memory,
   and prove it complete ([below](#an-inventory-that-misses-nothing)).
   List every route, window, view, dialog and popover.
2. For each, list its states: empty, loading, partial, full, error,
   offline, read-only, first run, signed out. One line per state, not
   one per screen.
3. List every control and its states: rest, hover, pressed, focus,
   selected, disabled, busy.
4. List every transient surface: toasts, menus, tooltips, confirmations,
   notifications, the tray or menu-bar icon, the app icon at every size.
   Every use of a shared dialog, sheet or menu is its own line.
5. List every surface the system draws around the app: launch and
   launch failure, permission prompts and the app's words before them,
   share sheets and file export, document viewers, keyboard and autofill.
6. List every process end to end: onboarding, sign-in, adding an account,
   sending, syncing, undo, deleting, settings changes, quitting.
7. List every motion: transitions, progress, empty-state scenes, and what
   reduced motion shows instead.
8. Walk the list in both themes, in every shipped language (with a
   pseudo-locale for long strings), at the largest text size, and in
   every orientation and device size the app allows.
9. Grade each item against the spec: matches, drifts, or misses the
   identity. Use the rules in [visual-craft.md](visual-craft.md).
   "Matches" needs a picture: a capture or a board, compared with the
   spec. An item nobody has looked at is "not seen", never "matches".
10. Redraw what drifts, misses or was not seen. Put it on the canvas with
    variants when the choice is open. Ask the owner. Strip the losers.
11. Fix canvas-versus-code drift as you find it: stale states, leftovers,
    features the canvas still calls "soon".
12. Build the agreed designs one to one, then capture the app and compare
    it with the canvas, object by object at full resolution
    ([design-before-build.md](design-before-build.md), "Pixel by pixel").
13. Re-audit the built app with a fresh critique. Iterate with the owner
    until the critique and the owner find nothing left to fix.

**Check.** The inventory exists as a checklist and passed its own check
([below](#an-inventory-that-misses-nothing)). Every line is marked
matches or fixed. The owner has seen every item in the identity, redrawn
or not. The last critique of the built app found nothing new.

## An inventory that misses nothing

**What.** The iteration 3 inventory is derived from the code by a method
that can be checked, then checked twice. A list written by reading and
remembering is a draft, not the inventory.

**Why.** Obálka's first iteration 3 inventory (2026-11-12) had 83 lines
and looked complete. The owner asked where the modals were. The modals
were there: 22 uses of the shared dialog, graded together as one
"matches" line that nobody had drawn. The backup and transfer screens
were one line each and hid 10 dialogs and two whole flows. A sweep then
found at least nine kinds of surface with no line at all: a launch
failure, a security notice, the permission explanations, file sharing,
the progress bar, and the largest text size among them. Fifteen lines
said "matches" without a picture. Each gap would have shipped in the old
look beside the new one.

**Apply.**
1. **Sweep the sources.** List every UI source file, every route, and
   every group of user-visible strings. Map each to inventory lines. A
   file or string group that maps to nothing is a gap.
2. **Count the shared pieces.** Search for every use of the shared
   dialog, sheet, menu, alert, toast and banner. Each use is a line,
   named by its title or trigger. The count on the list equals the count
   in the code.
3. **Split by state.** A screen with more than one state, flow or dialog
   gets a line for each. "The backup screen" is not a line.
4. **Get a second inventory.** Someone who has not seen yours (a person
   or a fresh agent) builds one from the code with the same headings.
   Compare line by line. Every difference is a gap in one of the lists
   or a mistake; resolve each before grading.
5. **No grade without a picture.** Grade from a capture of the app or a
   board on the canvas. Quiet chrome is drawn too; the owner judges
   whether it holds the identity.
6. **Record the proof** in the checklist: the files swept, the counts
   per shared piece, and who made the second inventory.

**Check.** Every UI file and string group maps to a line. The checklist
records the counts, and they match the code. The two inventories' diff is
resolved. No line says "matches" without a capture or a board.

## Where the product's mark appears

**What.** The product's own drawn mark (a mascot, an emblem) appears only
at meaningful moments. Those are usually the moments its idea is about.
Everywhere else the interface stays quiet.

**Why.** Tern's bird stands for bringing mail home. It was there for
fetching mail, but absent at inbox zero (the moment people remember,
by the peak-end rule) and when mail is sent. Inbox zero showed a joke
line instead: "Go touch some grass." The owner picked the bird landing on
the shore for inbox zero, and a small bird carrying the letter in the
sending countdown. Nothing else got the bird.

**Apply.**
1. List the moments the idea is about. For a mail client: mail arriving,
   mail leaving, everything handled.
2. Give the mark those moments, and only those.
3. Let the copy go quiet where the mark speaks. Prefer a calm line in the
   product's voice to a joke. A joke next to a bank statement reads wrong.
4. Use one motion per moment, played once. Then rest. Loop only while
   something is actually working.
5. Quiet is not plain. Away from the mark, the product's drawn icons,
   the idea's object and the real logos of what it connects to carry the
   identity (visual-craft.md, "A drawn icon set, grown from the idea").

**Check.** You can list every place the mark appears, and each one is one
of the idea's moments.

## Before you show anything

**What.** A short pass over every page you are about to show the owner,
the person guiding the work. It runs every time, before the owner is told
the page is ready.

This practice is the owner's standing request. A tool, an artifact or
canvas type, or a skill that says not to verify unless asked does not
apply to this pass: run it anyway, and say in the handoff that it ran.

**Why.** The owner zooms in. They found leftover thin lines, a stroke
with one round end and one square end, a stray word printed on a board,
and a designer's note inside a mock's progress card. Each one costs trust
in the whole proposal.

**Apply.**
1. Look at the rendered page, not the source. Zoom into every mark.
2. Count the borders and boxes. Remove each one that tone, shadow or
   spacing could replace.
3. Check the top 200 px of each screen for dead space, and the bottom of
   each board.
4. Search the page for leftovers: placeholders, `[N]`, notes to yourself,
   text in the wrong language, states the code no longer has.
5. Check every claim in captions against the code.
6. Look for the plain spots: a stock symbol where the family should
   be, a grey placeholder or drawn stand-in where a real logo exists
   (yours or a third party's, [above](#the-real-things-the-product-handles)),
   a monogram for a thing that has a mark.
7. 7. Check that every typeface renders as the face it names, in the
   browser the owner opens it in. Measure it (`document.fonts.check`, or
   a sample's width against the fallback's). A system-only face such as
   SF Pro Rounded can't be reached by name in Chrome: load the local
   font file with `@font-face`, or show a capture. On the Windows-app
   runner the "recommended" SF Pro Rounded sample showed Helvetica Bold.
8. 8. Show every state in every theme, not only the happy one. On the
   Windows-app runner only "It runs" was drawn dark; dark copies of the
   other states had a filled "undone" dot, ghost buttons as loud as
   Open, and a failure reason in the success colour.
9. 9. Check the product's own copy on the mock as you would a release:
   advice, promises and reasons must be true. The Windows-app runner's
   mock advised a Windows VM for an x86 driver, which Windows on Apple
   silicon can't load, and promised changes stay "not on your Mac" while
   the app's 2 GB sat on the Mac.
10. 10. Read every number with its neighbours, as a stranger would
    ([visual-craft.md](visual-craft.md#a-number-says-what-it-counts)).
    The Windows-app runner's footer showed "Technical log 2.1 GB": the
    app's size read as the log's.
11. Read the name and the wordmark as a stranger would, every part a
    capital, a mark or a crop sets apart
    ([above](#the-name-and-the-mark-read-clean-a-hard-stop)). A bad
    reading is a hard stop.

**Check.** The handoff message says these checks ran, on the rendered
page, and what they found.

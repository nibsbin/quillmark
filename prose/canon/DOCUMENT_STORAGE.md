# Document Storage Serialization

> **Implementation**: `crates/core/src/document/`

## TL;DR

`Document` is the typed in-memory model of a Quillmark Markdown file. Its
layout tracks the evolving Quillmark model and is **not** a stable interface.
To persist documents (e.g. in a database) without storing Markdown (whose
syntax also evolves), `Document` serializes to a **versioned JSON envelope**,
`StoredDocument`, whose wire format is frozen per schema version.

## When to use it

| Form | Round-trips? | Stable for storage? |
|---|---|---|
| Markdown (`Document::to_markdown`) | Yes | No: syntax evolves |
| `StoredDocument` JSON | Yes: lossless | Yes: frozen per schema version |

Use `StoredDocument` JSON whenever a `Document` must survive a process
restart or a crate upgrade: database rows, caches, message payloads.

What a schema-bound read hands a consumer is the values form: the stored value
with content as its codec's text, sparse, and carrying neither anchors nor
`$quill` ([SCHEMAS.md](SCHEMAS.md) § "The values form"). It is a projection,
never a row.

The plate JSON a render hands a backend is a lossy, one-way export,
crate-internal to `quillmark-core` and never a storage option.

## Design Principles

1. **Versioned envelope**: every blob carries a `schema` tag; readers
   dispatch on it and reject unknown versions.
2. **Frozen DTO per version**: each schema version has its own standalone
   type tree (`DocumentV0_92_0`, `CardV0_92_0`, …). These are never changed
   once shipped.
3. **Decoupled from the live model**: internal refactors of `Document` and
   its components only touch conversion code, never the wire format.
4. **Transparent API**: `Document` serializes through the envelope via
   `#[serde(into / try_from)]`; callers use `serde_json` directly.

## The Format

The current schema (`quillmark/document@0.124.0`) carries each card's full
ordered payload: typed `$` system metadata, user fields, and YAML
comments interleaved in source order: as a single discriminated-union
item list. This is what makes inline-comment preservation symmetric across
the `$`/non-`$` boundary. A field item is `{type: field, key, value}`;
`body` is the canonical `Content` embedded structurally (a nested
object, not a markdown string); see Byte-stability.

```json
{
  "schema": "quillmark/document@0.124.0",
  "main": {
    "payload": {
      "items": [
        { "type": "quill", "value": "usaf_memo@0.1" },
        { "type": "kind",  "value": "main" },
        { "type": "ext",   "value": { "presentation": { "title": "Greeting Card" } } },
        { "type": "field", "key": "title", "value": "Hi" }
      ]
    },
    "body": { "islands": [], "lines": [ { "containers": [], "kind": "para" } ], "marks": [], "text": "Hi" }
  },
  "cards": [ ... ]
}
```

`StoredDocument` is an internally-tagged enum (`#[serde(tag = "schema")]`);
each variant carries a frozen DTO tree. Quill references are stored as
strings (parsed back via `QuillReference::from_str`). The discriminator on
payload items is `type` (not `kind`) to keep it unambiguous next to the
`$kind` metadata semantic. The full variant set is `quill | kind | id |
ext | seed | field | comment`; the `ext` and `seed` variants carry the
`$ext` / `$seed` maps verbatim and are stripped from the plate JSON
before backends see it.
Load-time warnings (a parse's, plus the `conform::*` diagnostics when the
document came through the bound door) live on the `Parsed` record, not on
`Document`, so they never reach this format; the bindings stash them on
their `Document` handle as session state and exclude them from `equals` and
the DTO alike.

### Legacy schemas (V0_116_0, V0_115_0, V0_112_0, V0_93_0, V0_92_0, V0_82_0, V0_81_0)

Documents written under `"schema": "quillmark/document@0.116.0"` carry the
current tree, over the content vocabulary without `element` or a list item's
`checked` (§ Content vocabularies), and the hop decodes the `body`.

Documents written under `"schema": "quillmark/document@0.115.0"` carry the
V0_116_0 tree, and the hop is a retag. A field item under it or any older tag
may also carry `fill` and, from V0_92_0, `nested_fills`; the read passes over
both and keeps the `value`.

Documents written under `"schema": "quillmark/document@0.112.0"` carry the
V0_115_0 tree, over the content form that carried a `loss` class on
every island and spelled a block island's line `{"kind":"island"}` rather than
`{"kind":"para"}`. The line kind is derived, not stored: a lone island slot's
line is a paragraph, and whether that slot's markup is a block is the island
*type*'s to say. The hop is a retag, and the V0_116_0 hop's `body` decode reads
the spelling: the decoder reads `island` wherever it meets it and ignores
`loss`, permanently, because the same spellings rest untagged inside every
`richtext` field.

Documents written under `"schema": "quillmark/document@0.93.0"` carry the
V0_115_0 tree, over the content form that spelled a built-in's payload
as named siblings (`{"kind":"heading","level":1}`). The hops are retags and the
same `body` decode: the content decoder reads that spelling wherever it
meets it, which it must, because most stored content in that spelling reaches no
migration at all — a `richtext` field rests as a content object inside an opaque
payload value, under no schema tag of its own.

Documents written before `0.93.0` carry
`"schema": "quillmark/document@0.92.0"` and store the card `body` as a
markdown string rather than the embedded canonical content. Readers accept
them and migrate forward to V0_124_0 on load; writers do not produce this
shape. The one hop that can reject is the body cold-import (see
Byte-stability).

`"schema": "quillmark/document@0.82.0"` is the V0_92_0 item list without
`$seed`, plus `$id`. Its tag names a shape **union**
rather than one frozen format: `$ext` entered under it unchanged, and many
release versions stamped it. The reader accepts the union, which is what
lets a row from any of those writers load.

That hop is **lossy**: `$id` is dropped, with the inline comment trailing it.
The live model has no counterpart for it, so the alternative is refusing the
row; `$id` reached no backend, which is what makes dropping it the cheaper loss.

`"schema": "quillmark/document@0.81.0"` is the oldest tag that exists, not
just the oldest one read: `0.81.0` is where `Document` serialization begins, and
no build before it serialized a `Document` at all. Every stored blob therefore
carries one of the eight tags this page names, and the reader set is complete. Its shape
is pre-unification: a separate `sentinel` beside a `frontmatter` item list. It
carries neither `$id` nor `$ext`, so its hop to V0_82_0 is lossless.

A composable card naming no `$kind`, which 0.115 parsed as a card and stored,
folds on load, under any tag, into the body above it: its fields and comments
as an untagged backtick code block, whose text is admitted as a body import
admits it, then its own body. Its `$ext` drops, since `$ext` reaches no render
and the body does. What the fold lands is new content: an island id the body
above already holds is minted anew, the next `isl-{n}` past the highest in
either body (§ Island-id determinism), and an anchor whose id it already holds
drops whole, since the engine mints no anchor id (§ Anchor-id identity). Every
later card moves up one index.

## Byte-stability

Serialization is **byte-deterministic** within a given schema version:
equal `Document`s (by `PartialEq`) produce byte-equal JSON, and the same
document re-serialized in any later patch or minor release tagged with
the same `schema` produces the same bytes. This is load-bearing for
consumers that content-hash stored documents (template-divergence
detection, cache keys).

**Two disciplines in one envelope.** The outer envelope: struct field
order, the `cards` array, payload field values: stays compact,
insertion-ordered `serde_json`: `serde_json::Value` inside payload field
values keeps YAML insertion order via the workspace's
`serde_json/preserve_order` feature, and no whole-envelope key sort is
applied. Every `body` subtree, by contrast, is the recursively key-sorted
**canonical content form** (`CanonicalContent` in `dto.rs`): byte-identical
to `rt.to_canonical_json()` and independent of `preserve_order`, even in a
consumer crate graph that lacks the feature. Sortedness is semantic
*inside* the content (mark/island/attribute order carries no meaning, so the
serializer commits to one bit pattern); insertion order is semantic
*outside* it (payload item order is source order, and matters).

**Both directions validate.** `CanonicalContent` checks the body's
invariants on the way out as well as in, failing the write with a serializer
error. The token a body rests on (`Normalized`) states that
`Content::normalize` has run, which is weaker than validity: `validate`
refuses only what `normalize` cannot repair — a forbidden character, two
counts that disagree, a range or depth past a bound, a colliding id — and
`Card::overwrite_body` takes a caller's content on that token alone. A store
that checked only on load would accept bytes it could not read back.

The guarantee follows from: struct field order is fixed in the frozen
DTO tree; `Vec` fields preserve order by definition; the two disciplines
above each hold at their respective level. No whitespace normalization is
applied: the output is `serde_json`'s compact form otherwise. Bumping the
`schema` version is the only event that may change the byte layout of a
document written by the current writer.

**Resting form.** Byte-equality is over `Document` values, so it is only
as useful as the model's agreement on what a given document *is*. A
content field has one resting form per codec: a `richtext` field rests as
the canonical content object, a `plaintext` field as its literal string
([SCHEMAS.md](SCHEMAS.md) § "Content fields rest per codec").
`Quill::conform` is what holds that: it walks a document's declared
content fields through the same strict write the typed writer commits
through, so a parse-then-conform and a typed write of the same values are
byte-equal. Documents that have converged hash equal when they are
semantically equal, so `equals` and content hashing hold for content
fields by construction rather than by construction history.
Non-content-typed fields keep their authored shorthands (`qty: "3"` stays
a string until something writes it); the typed write remains their
canonicalizer.

A document that entered through the transport door (`Document::parse`, a
stored row, `store_field`) rests as authored until it is conformed. That is
a named state, not a second resting form: it is readable, round-trippable,
and one bound load away from converging.

A comment's text rests without the whitespace ending it, as a parse reads its
line, so a stored row holding such text loads without it and rewrites once.

**Migrated rows: a conditional caveat.** The guarantee above is unconditional
for a document the current writer serializes directly. A row still carrying
a legacy schema tag migrates forward on read, and the `0.92.0` hop
cold-imports the stored markdown `body` string through the same
Markdown → richtext path `Document::parse` uses. Byte-stability of
*that* row across a crate upgrade is therefore conditional on
`pulldown-cmark` parsing the body the same way: a forced parser or security
bump can move the migrated bytes even though the schema tag does not
change. Two ways to manage this:

- **Read-repair.** Rewrite a row under its current schema tag once it has
  been read and migrated, so the content form: not the legacy markdown
  string: becomes its byte-stable resting state. This is the same lane
  `Quill::conform` uses, the second named driver of read-repair byte
  movement: a row read through the bound door converges to canonical rest
  and is eligible for rewrite under its current tag. Neither is a
  schema-version event; a population converges once and then holds.
- **Accept the movement.** For rows left un-repaired, treat a forced
  parser/security bump as either a schema-version event (if a hard
  guarantee is required) or an accepted, logged hash movement on
  not-yet-migrated rows.

## Content vocabularies

The envelope's version-and-reject discipline covers the document's **shape**:
the schema tag, the DTO tree, the keys a `body` object carries. The content's
four discriminators are covered by their own rule: each is a **closed set**.

| Axis | Members | Rust type |
|---|---|---|
| Line `kind` | `para`, `heading`, `code`, `rule` | `LineKind` |
| Container | `list_item`, `quote`, `element` | `Container` |
| Mark `type` | `strong`, `emph`, `underline`, `strike`, `code`, `link`, `anchor` | `MarkKind` |
| Island `type` | `table`, `image` | `IslandType` |

A name outside one of them is `ParseError::UnknownName { axis, name }` at every
decoder, both lanes, so **a row holding one does not open**. Refusing is the
only reading that keeps the reader honest: projecting an unrecognized `kind` as
`para` would re-encode the row as `{"kind":"para"}`, moving canonical bytes on a
read with no edit (§ Byte-stability), and dropping the value loses content on a
mere open. Carrying the name opaquely and refusing only to *project* it holds
the bytes, and costs totality instead: a projection over a container tree is
total over a `Normalized` body, and a region no projection reads has no defined
result. A malformed discriminator is a different failure and stays
`ParseError::Shape`: the closed set answers for names, and a non-string is not a
name.

`element` is a closed member over an open payload. Its `attrs` bag holds the
element's name under `$name`, any carrier element name but the reserved
`table` and `anchor`, beside its attributes, each a string under a name
in the carrier's attribute grammar ([markdown-spec.md](../references/markdown-spec.md) §6.4).
No attribute name opens with `$`, so the two never collide, as a card's `$kind`
never meets a field. A new element name is no storage event, since no reader is
frozen at a set of names; the member's arrival was one (`0.124.0`). A bag
outside the grammar is `ParseError::Shape` on both lanes. Container identity
compares the whole bag, `$name` among it.

A task item's `checked` is a `list_item` bag entry, `true` ticked and `false`
open, absent on an item that is no task. It is the item's, like `ordinal`: two
items differing in it sit in one list run. A reader drops a bag key it does not
name, so a build without `checked` would read a task list as a plain one and
save it so; the key arrived under the tag that brought `element` (`0.124.0`),
which that reader refuses.

`island` is the one name a decoder reads that no encoder writes, and the
exception that shows the rule's price. It names the line a block island sits on,
a fact the island's own type settles, so the decoder reads it as `para` — the
re-encode the paragraph above calls dishonest, made honest by the `@0.115.0`
tag that says the writer moved. The tag
covers the rows it stamps and nothing else: the same spelling rests untagged
inside every `richtext` field, which is why the read is permanent rather than a
migration hop (§ "Adding a Schema Version").

The consequence, and the point: **adding a member to any of these vocabularies
is a storage-version event.** An older reader refuses a row carrying a newer
build's construct, and the schema tag is what lets it say "build too old"
rather than "corrupt" (§ Schema Versioning). The tree freeze such a bump needs
is mechanical — the DTO shape is unchanged, so the new version's tree is the
old one and the `TryFrom` hop is the identity (§ Adding a Schema Version).

**A `Content` stores its value, not how the value came about.** What a markdown
import drops on the way in — a table cell's inline image, whose alt text lands
as the cell's text and whose url lands nowhere — is a fact about that import,
not about the island it mints: two tables whose `props` are equal are equal,
however each was written, and the projection has no syntax to carry the
difference back. So the canonical form is `{id, type, props}` and holds no
fidelity class beside them: such a record is not re-derivable from the row that
would carry it, and does not survive a `to_markdown` → `from_markdown` hop.
Surfacing a drop belongs to whoever runs the import, where it happens. The
import reports the raw tags it drops beside the content ([markdown-spec.md](../references/markdown-spec.md) §6.2 names the
silent ones), and core surfaces those of a body's parse and of a revise as
`parse::dropped_construct` ([ERROR.md](ERROR.md) § "Warning flow"); a cell
image's url drops unreported.

**Container identity is path plus contiguity, and `instance` is what completes
it.** Two adjacent lines sit in the same container iff their whole container
path is equal, so without a discriminator two adjacent runs of one shape read as
one: `[Quote], [Quote]` would be a single two-paragraph quote, and two one-item
lists a single item with an unnumbered continuation paragraph. `instance` is the
field that breaks that tie, on every container arm, which is why the round trip
is a *total* promise rather than one holding up to an adjacency quotient. `Content::normalize` canonicalizes it to `0`, flipping to
`1` only where the adjacent preceding sibling run would otherwise weld, so a
document needing no discriminator carries none and its stored bytes are the
bytes it had before the field existed (§ Byte-stability). That is why the key
was additive within `@0.93.0` rather than a schema-version event: no blob
written before it moves. The cost is in the other direction, and only for a
document that spends the key — a build predating the field ignores it and reads
the two runs welded, so a row written here and re-saved there loses the
boundary. A container field added later inherits that trade, since a reader is
frozen at the vocabulary it shipped with. The Markdown
projection spells the same boundary with the idiom CommonMark already reads: a
change of bullet char (`-`/`+`) or of ordered delimiter (`.`/`)`) for lists, the
blank line for quotes, and for an element the tag pair each run writes.

The omission is every encoder's, storage and the binding seam alike
(`serial::to_canonical_value` is the only one). A spelled zero decodes to the
same value, so a producer holding an older read writes it straight back; it is
just not what an encoder emits, which is what keeps the byte-stability above
unconditional. A binding's read type therefore spells `instance` optional
([BINDINGS.md](BINDINGS.md)).

**A new container owes its projections a separator.** `instance` makes the
boundary storable; it does not make it *writable*. A container whose Markdown
spelling cannot separate two adjacent instances has a boundary in storage that
the projection drops, so `from_markdown(to_markdown(rt)) == rt` fails on
re-import — the model reads one container where it stored two. Spell the
separator when the container is specced, not after: a container defined on
CommonMark §5.1's terms (a per-line marker, blank-line terminated, as
`Container::Quote` is) gets one for free, because the blank line already ends
it. One defined on §5.2/§5.3's terms (a list, which a blank line leaves open)
does not, and needs the marker alternation `Container::ListItem` uses. The same
obligation falls on the Typst lowering: two adjacent instances must not lower
into one another's markup.

Unknown *keys* survive in designated carriers only, and the boundary is worth
stating because it is not the discriminator boundary:

- **Opaque carriers keep what they hold.** Island `props`, a table island's
  top-level props, and a table **cell's** own keys all round-trip untouched.
- **Envelopes drop what they do not name, by design.** An island, line, mark, or
  container object is decoded into a struct and re-minted from its fields, so an
  unrecognized sibling key beside `id`/`kind`/`start` does not survive. Growing
  those shapes is a schema event; that is what the envelope's version-and-reject
  discipline is for.

A table cell sits on the first side because it never became a struct, and it
earns the place: cells are where the `table` type is likeliest to grow
(`colspan`, `rowspan`, a per-cell style handle). Canonicalization therefore
rewrites a cell's `text` and `marks` in place rather than minting a fresh
`{text, marks}` object.

A table island's props name `header`, `rows`, `aligns` (one per column:
`none`, `left`, `center` or `right`) and three layout keys, each absent at its
default:

| Key | Value | Default |
|---|---|---|
| `widths` | one entry per column, an integer weight from 1 to 2⁵³ − 1 or `null` for an auto-fit column; settled to the column count | every entry `null` |
| `align` | the table's placement: `left`, `center` or `right` | the plate's placement |
| `headless` | `true`: `header` is the first body row, drawn as one | a header row |

`widths` are weights, not lengths, so each plate decides what full width is.
The keys ride the opaque props carrier, which an older reader round-trips, so
adding them is no storage-version event, and a later props key joins the same
way.

A cell names two keys of its own, each absent by default:

| Key | Value | Default |
|---|---|---|
| `align` | the cell's horizontal alignment: `left`, `center` or `right` | its column's `aligns` entry |
| `valign` | the cell's vertical alignment: `top`, `middle` or `bottom` | the plate's |

A cell's value equal to its column's is an override that stays when the
column changes. A table or cell key holding a value outside its set is read
as absent and rides untouched, as an unnamed key does, so
`from_markdown(to_markdown(c)) == c` holds where every value is in its set.

Two rules bound the payload:

- **Payload depth is capped at `MAX_JSON_DEPTH` (128).** Island `props` is host
  JSON of arbitrary shape, but not arbitrary depth: key canonicalization, the
  content-hash key, and `serde_json::Value`'s own `Drop` each recurse one frame
  per level, so an unbounded bag overflows the stack: on wasm32, a trap that
  takes the module down rather than an error the host can catch. The cap is the
  one `serde_json::from_str` already enforces, so it refuses nothing a stored
  blob can carry. It is stated on its own because the `Value` lane — the
  host-authored one, which `overwrite` reaches — is not parsed from a string, so
  nothing else bounds it. A bag is refused where the decoder reads it off the
  wire, before it is cloned into the model; `Content::validate` restates it as
  `Invariant::JsonTooDeep` for content that never went through a decoder. This
  is `Invariant::NestingTooDeep`'s container cap on the payload axis.

- **Payload rides `attrs`, for every member.** A `heading`'s `level`, a `code`'s
  `lang`, a `link`'s `url`, a `list_item`'s shape and an `element`'s name and
  attributes are all `attrs` entries:
  `{"kind":"heading","attrs":{"level":1}}`. The envelope keys stay siblings —
  `kind`/`type`/`container`, `containers`, `continues`, a mark's `start`/`end`,
  a container's `instance` — because they belong to the object rather than to
  the member it names. An empty bag is omitted, on the rule `continues: false`
  already follows: presence is a pure function of the value, so `normalize`
  collapses `{}` and an absent bag to one spelling.

  A foreign bag key on a built-in is permitted and drops unread: the decode
  reads the entries the member names and re-mints from its fields.

  One spelling per name is also what makes the canonical mark order a function
  of the bytes. `MarkKind::sort_key` is the `(type, attrs)` pair the wire
  carries, read back off the value rather than spelled per arm, so adding a
  member reorders nothing already stored (§ Byte-stability).

The lanes still split, on what is now the only ambiguous shape — a built-in's
payload spelled as a **named sibling**, which is how every release through
`@0.93.0` wrote it:

  - **The storage lane reads it, and must.** `serial::payload` falls back to the
    sibling when the bag is absent — an *empty* bag being an absent one here as
    everywhere. Most stored content cannot be migrated: a `richtext` field rests
    as a content object inside an opaque payload value, under no schema tag, so
    the decoder's tolerance is the only thing that opens it. It is also not
    retirable on tag evidence, no tag naming those rows. Read-repair converges
    the population; cold rows keep it alive.
  - **The authored lane rejects it.** A legacy payload sibling is a shape error
    (`serial::line_kind_from_authored_value` and its container and mark twins
    for the op wire, `serial::from_authored_value` for a whole content). A host
    writing it now holds a stale copy of the encoding, and where a bag sits
    beside it the sibling it meant is not the one the decoder reads. Reads that
    hand back stored content (`exportMarkdown`, `rebase`) are storage-lane, not
    this one.

  Both read one frozen table (`serial::legacy_*_keys`): the fallback reads
  exactly the keys the rejection refuses, so a key a later promotion adds is in
  neither and the two spellings stay split by release rather than by which names
  a build knows.

  The authored lane is `overwrite` and the op wire. Two doors that take a whole
  content sit outside it. **`CardInput.body`** decodes storage-lane
  (`wire::body_from_wire`, through `Codec::decode_field`): every `Card` a read
  hands back is a valid `CardInput`, so the card wire must accept whatever a
  read emits, a stored-only tolerance included. A **typed field
  write** does too: `document::canonical_richtext_value` shares that entry point
  with a quill's schema literals, which are read out of a `Quill.yaml` that may
  predate the release. Both re-canonicalize what they decode, so the value rests
  in the current spelling either way.

The same split governs a **malformed table-cell mark**. Storage skips it:
`serial::parse_cell` is lenient, and normalization makes the skip permanent. The
authored lane refuses it, because a host's malformed mark vanishing with no
signal is the silent corruption the split exists to catch.

The split stops at *shape*. A cell mark whose `type` is outside the vocabulary
is refused on **both** lanes, at the decoder
(`IslandType::reject_unknown_cell_mark`), because the lenient read is exactly
what would make it silent: `canon_cell` re-mints each cell from what
`parse_cell` returned, so a skipped name leaves the stored bytes on a read with
no edit — the byte movement § Content vocabularies refuses the row to prevent.
The mark axis is closed everywhere a mark is spelled, cells included.

It governs a **value the markdown projection cannot write** as well: a code
fence's `lang` outside the identifier shape it is emitted in unquoted, and a
link or image `url` carrying a line ending, which CommonMark admits in no
destination form. The authored lane refuses both, so a host learns at the write
that its markdown would come back without the fence header or the mark. Storage
takes what it holds and the projection settles it — `import::sanitize_lang`
reduces the `lang`, `export::emit_url` percent-encodes the line ending, and the
encoded url is what a re-import reads back.

The url rule is on the lanes that **store** one, not on `MarkOp::Remove`, which
matches on kind equality against a mark the field already holds: a url in the
model has no second spelling, so refusing it there would make a stored link
unremovable.

It governs a **block-only island's placement** too. Markdown writes a `table` as
a block (`IslandType::block_only`, which an inline `image` is not), so a
slot sharing its line with prose has no inline spelling: written there it lands
as pipes inside the paragraph, which re-imports as prose with the island gone.
The authored lanes refuse the placement — `ApplyError::BlockIslandNotAlone` from
`IslandOp::Insert` and from a `Set` that retypes an inline island, a shape error
from `serial::from_authored_value` — so a host learns at the write. The line
itself is a `para` either way: the block is the slot's markup, and the type is
the only thing that says so. Storage takes
what it holds and the **mint** settles it: `Content::normalize` breaks the line
around the slot, so the prose on each side becomes its own block and the island
keeps the line its markup needs. The break lands once, on the way in, so the
markdown write reads a shape that is already right rather than repairing one on
the way past.

The opaque props are hash input like everything else in the canonical form, so
they are recursively key-sorted along with the rest (see Byte-stability). Also a
schema event: a change to the content object's own structure — a new top-level
key beside `text`/`lines`/`marks`/`islands` — or a changed meaning for an
existing discriminator.

## The two id handles

Islands and anchors each carry an id, and both are the same handle: **opaque,
unique within a scope, hash input, stable for the session, rebased through edits
and never rewritten.** They differ on one axis: **who mints one, and why only
they can.** Uniqueness scope, collision response, and markdown round-trip all
follow from that.

|                     | Island `id`                                        | Anchor `id`                                        |
| ------------------- | -------------------------------------------------- | -------------------------------------------------- |
| Minted by           | the engine at import or fold, the caller on insert | the caller                                         |
| Because             | content determines it: the nth island minted      | the referent is external; no content determines it |
| Unique across       | the `Content`'s islands                            | the `Content`'s prose marks                        |
| Required            | yes: `insert` rejects the empty id                 | yes: the empty id is rejected                     |
| On collision        | `insert` rejects; `validate` scans                 | `add` rejects                                      |
| Markdown round-trip | re-minted identically                              | carried by revise; spelled read-only by the annotated export |

A card is addressed by index and carries no id handle. A consumer needing a durable per-card key carries one in `$ext` under its own namespace ([CARDS.md](CARDS.md) § Out-of-band Metadata), which the engine round-trips and never interprets.

Each section below states one handle's policy whole.

## Island-id determinism

An island's `id` is part of the canonical form (`{id, type, props}`),
so it is hash input like every other field, and byte-stability's promise:
equal content → equal bytes, *whatever the producer*: requires that equal
islands carry equal ids. The rule: **an id is a deterministic function of
content, never drawn from an ambient source** (RNG, wall-clock, UUID,
allocation identity, session or process state). An ambient id would make
re-importing the same markdown yield different bytes for the same document,
silently breaking divergence detection and cache keys.

The normative scheme is the importer's positional `isl-{n}`: the nth island
minted takes `isl-{n-1}` (`mint_island`), so cold import is a pure function
of its markdown; export drops ids and re-import re-mints the same sequence.
Ids then travel with their island across edits: deleting a slot drops that
island and survivors keep their ids, so an id is *stable within a session*,
not re-derived from position. The invariant that holds for every `Content`,
checked by `Content::validate`, is therefore **uniqueness**
(`Invariant::IslandIdCollision`), not `id == isl-{index}`: after an edit
`isl-1` may legitimately sit at index 0.

The id stays in the hash input, so "canonical bytes == hash input" holds exact: no id-stripping, no separate hash form.

The importer is not the only minter: `IslandOp::Insert` carries the id of the island it lands, and the apply refuses the empty id and one already live in the field (`ApplyError::EmptyIslandId`, `ApplyError::IslandIdCollision`), since `IslandOp::Set` addresses by it. That producer is bound by the same never-ambient rule: continue the positional sequence past the field's highest `isl-{n}`, never a UUID, a clock reading, or a session counter. Import purity is unaffected either way, since export drops island ids and no edit-minted id reaches markdown; the rule holds at edit time so two producers making the same edit reach the same bytes.

A markdown revise (`diff_import`, `rebase`, every `revise` verb) keeps the ids too, though its import mints positionally: an island equal to a stored one in the longest run of equal islands the two sequences share keeps that island's id, as does each island of a stretch between two of those where both sides hold as many islands of the same types in order (a table edited in place). Every other island the revise lands mints past the highest `isl-{n}` the field held before it, so none takes a dropped island's id.

The continuation rule mints a *new* island. Re-landing a dropped one is not a mint: the delete freed the id and it travels back with its island, so restoring a deletion restores the bytes. A pasted copy of a live island is new and mints fresh. Swapping the two cases is `IslandIdCollision` on the paste, or a silently renamed island on the restore.

The two compose because minting reads the *live* ids: deleting the highest island frees its number for the next mint, and restoring that delete would then collide. Linear undo never reaches that state, since a mint made after a delete is undone before it. A producer with non-linear history (selective undo, a merge) owns the case, and the apply refuses it rather than aliasing two islands.

## Anchor-id identity

An anchor (`MarkKind::Anchor { id }`) sits at the caller-minted end of the mint
axis (§ The two id handles) because it has **no markdown codec**: it
names an external referent (a comment thread, an editor bookmark) that no
content determines. The never-ambient rule therefore cannot apply, and need not:
that rule exists to keep *import* a pure function of markdown, and import mints
no anchor, so equal markdown still imports to equal bytes.

The policy: **an anchor id is caller-supplied, unique per `Content`, opaque and
invariant while the mark lives; the mark is best-effort under edits and
read-only in markdown.**

- **Caller-supplied.** The engine mints no anchor id and cannot: only the
  consumer knows the referent. Each consumer (editor, MCP writer) supplies its
  own; the runtime persists it verbatim. Engine-minting is a non-goal by
  design: a counter is history-dependent (the same final content reached two
  ways carries different ids: the ambient source the twin rule forbids) and
  forfeits referent-convergence (two `add`s for one thread would mint two
  handles). A client wanting generated ids mints them client-side and supplies
  them; the auto-fallback middle ground (engine mints when the caller omits) is
  a non-goal too.
- **Unique per `Content`.** `add` *rejects* a collision: not replace (which
  silently retargets a live thread) nor coexist (already incoherent: an anchor
  is *the* handle `RemoveAnchor { id }` retains-out, so a shared id makes
  removing one destroy both). The empty id is rejected as a degenerate handle.
  Enforced at op time in the `Add` arm and as a `Content::validate` invariant
  (`Invariant::AnchorIdCollision`, the uniqueness scan the island check shares).
  Scope is prose `marks`: an anchor inside an island cell is unreachable by
  `RemoveAnchor` (it scans prose marks only), so it sits outside the op surface
  and outside this uniqueness check: explicit partial enforcement, not silent
  half-enforcement.
- **Opaque and invariant.** The runtime never rewrites an id. Positions rebase
  through splices (`map_pos`); the id passes untouched. A mark whose text is
  deleted, or moved-and-rewritten in one round, drops *whole*: never
  partially, never re-id'd (the documented diff-rebase residual). A revise
  diffs by line, then by character within a line it rewrites. Replaced lines
  pair from either end of their run, old with new, while a pair is a rewrite:
  each line at most 5,000 characters, the two sharing half their words or
  more, and neither occurring whole on the other side. A mark keeps its place
  through such a rewrite wherever its text is untouched. A line replaced by different text is a deletion, and a mark
  in it moves only where its text, four characters or more, recurs in text the
  revise inserted, its first occurrence there taking it; a point mark recurs
  by the text beside it.

No markdown round-trip guarantee: `to_markdown` emits nothing for an anchor and
import mints none, so a cold export→import loses every anchor.

The annotated read (`export::to_markdown_annotated`,
`Document::to_markdown_annotated`) spells each prose anchor as
`<qm-anchor ref="ID"></qm-anchor>` at its start, a spelling a cold
import drops unreported ([markdown-spec.md](../references/markdown-spec.md)
§6.4).

- A range anchor reads as its start, and keeps its range through `revise`.
- A code-block line, a block island's line and an empty line hold no tag. A
  line whose tags in place would change what it imports to holds them at its
  end, or none where that changes it too.
- The read lists every prose anchor with the text of its line, spelled or not,
  so a consumer locates the anchor whose tag a writer lost. An anchor in a table
  cell is outside the read, as it is outside the op surface.

Anchors are edit-lane infrastructure: they survive only through diff-rebase
(`revise` / `rebase`). A whole-document markdown write keeps them through
`Document::revise`, which aligns cards by `$kind` and text and rebases each
aligned body and content field; a prose anchor on a card it cannot align, or
one the diff drops, drops, and the receipt names it. An anchor in a table cell
drops on every markdown write, and no receipt names it. Reading the annotated
markdown and writing it back through `revise` keeps what a write of the plain markdown
keeps: the import drops the tags, and the read shows a writer where each
anchor sits. Non-rendering is a property of
review-time metadata, not a gap; a future render projection (proof annotations,
PDF destinations) would render the referent or a position, never the id, so
this policy holds either way.

## Schema Versioning

The schema version is tied to the **crate version at which the `Document`
wire format was last changed**: not the running crate version. The
current format was fixed in `0.124.0`, so the version tag is
`quillmark/document@0.124.0`; every later patch release writes that same
value, because patches do not change the format.

The format is the *bytes*, not only the envelope: `0.115.0` left the DTO tree
untouched, dropped an island's `loss` key and retired the `island` line kind
(§ Content vocabularies), which is a format change because the writer emits
different bytes for the same document — every document holding an island.

`0.92.0` is a unified payload-item list (typed `$` entries living alongside
user fields and comments in a single `Vec<PayloadItem>`) and the `seed`
payload-item variant (the `$seed` per-card-kind overlay map).
`0.93.0` leaves the payload model unchanged and instead embeds the card
`body` as the **canonical content**: structurally, as a nested object, not a
markdown string (see Byte-stability). `0.112.0` leaves the tree unchanged in
turn and moves every built-in's payload into `attrs` inside that content.
`0.115.0` leaves it unchanged again, drops an island's `loss` and spells a
block island's line `para`. `0.116.0` writes a field item as
`{type: field, key, value}` and refuses a document, card, payload or payload
item carrying a key its type does not name, where every earlier tag reads past
one. `0.124.0` leaves the tree unchanged, adds `element` to the container
vocabulary and `checked` to a list item's `attrs`.

The V0_92_0 hop cold-imports the stored markdown `body` string through the same
Markdown → richtext path `Document::parse` uses, so a pathologically
over-nested legacy body is rejected (`StorageError::Malformed`) rather than
silently truncated. The V0_116_0 → V0_124_0 hop decodes its raw `body`, and
can reject for the same reason a load can; the V0_93_0 → V0_112_0,
V0_112_0 → V0_115_0 and V0_115_0 → V0_116_0 hops are retags, every tree up to
V0_116_0 spelling `body` raw and that one decode answering for each spelling.

`0.81.0` is the oldest tag read, and migrations chain
(`V0_81_0 → V0_82_0 → V0_92_0 → V0_124_0`, with
`V0_93_0 → V0_112_0 → V0_115_0 → V0_116_0 → V0_124_0` beside it); only the
newest DTO converts to the live `Document`. The V0_92_0 chain lands on V0_124_0
rather than passing through V0_116_0: a cold import
yields the live content, and re-spelling it *back* to a raw `body` only to read
it forward again would need an encoder for that form, which this crate lacks.
The `V0_81_0` hop is structural, the `V0_82_0` hop is lossy in exactly one place
— `$id` is dropped (see "Legacy schemas").

## Adding a Schema Version

When the `Document` wire format changes again:

1. **Freeze** the current `DocumentV0_124_0` type tree: leave its struct
   /enum definitions and serde derives untouched so existing rows still parse.
   Replace any field whose type tracks the live crate — `CanonicalContent` is
   the one — with raw `serde_json::Value`, or the frozen tree will *write* the
   new format under the old tag.
2. **Remove** the conversions binding the old DTO to the *live* `Document`
   (`From<&Document>` and `TryFrom<… for Document>`): a frozen tree cannot
   convert to a model it predates, and step 3 supersedes them.
3. **Add** a new frozen tree `DocumentV0_NN_0` reflecting the new model,
   plus its `From<&Document>` and `TryFrom<… for Document>` conversions.
4. **Add** the `StoredDocument::V0_NN_0` variant, tagged
   `#[serde(rename = "quillmark/document@0.NN.0")]`.
5. **Write the migration**: `From<DocumentV0_124_0> for DocumentV0_NN_0` if
   the mapping cannot fail (a purely structural rename/restructure, or a retag
   like `V0_112_0 → V0_115_0`), or `TryFrom<DocumentV0_124_0> for DocumentV0_NN_0`
   if it can reject, as the V0_92_0 cold-import does for an over-nested legacy
   body and the V0_116_0 hop does for a body that will not decode. This is the only real labor: it
   encodes how old fields map to the new model (renames, restructures,
   defaults for new fields, and: for a `TryFrom` hop: which malformed inputs
   get rejected).
6. **Extend** the reader. Each older blob migrates to the newest DTO, hopping
   where a hop exists and entering directly where re-spelling backwards would
   need an encoder the crate lacks. Every arm below the newest is
   fallible today, so every one threads `?`:
   ```rust
   match stored {
       StoredDocument::V0_NN_0(p) => Document::try_from(p),
       StoredDocument::V0_124_0(p) => Document::try_from(DocumentV0_NN_0::try_from(p)?),
       StoredDocument::V0_116_0(p) => Document::try_from(DocumentV0_NN_0::try_from(
           DocumentV0_124_0::try_from(p)?,
       )?),
       StoredDocument::V0_115_0(p) => Document::try_from(DocumentV0_NN_0::try_from(
           DocumentV0_124_0::try_from(DocumentV0_116_0::from(p))?,
       )?),
       StoredDocument::V0_92_0(p) => Document::try_from(DocumentV0_NN_0::try_from(
           DocumentV0_124_0::try_from(p)?,
       )?),
   }
   ```

**A migration reaches the `body` and nothing else.** Every other stored content
— a `richtext` or `plaintext` field, a `$seed` overlay — sits inside an opaque
payload value carrying no schema tag, and a walk cannot tell one from host data
that merely looks like it (`$ext` is arbitrary by contract). So a change to the
*content* encoding is not migratable, and has to be readable instead: the
decoder reads the old spelling wherever it meets it, and the schema bump records
that the writer moved. Design a content change so a decoder can absorb it, or it
cannot ship. The reader that absorbs it is permanent: the untagged half is
reachable by no hop, so no later retirement frees it (`island` is the standing
case, § Content vocabularies).

A new frozen DTO can also reject at parse time through a custom
`Deserialize` rather than through a `TryFrom` migration: `CanonicalContent`
(the current `body` field's type) normalizes and validates the embedded content,
failing with a serde error before any `TryFrom` in the chain above runs.
Design a new DTO's `Deserialize` to fail the same way if it embeds
structured (non-string) data of its own. Freezing it per step 1 moves that check
into the hop.

Old and new DTOs **coexist** in `dto.rs`, so a row written by any
still-supported past version always loads. Migrations chain
(`V0_92_0 → V0_124_0 → V0_NN_0 → …`); only the newest DTO converts to the live
`Document`, so each migration step stays small as versions accumulate. The
cost is one frozen type tree per schema version plus one migration function
per version bump.

A legacy variant may be **retired**: its DTO tree, migration, and tests
deleted: once a product/release-history call confirms no stored population
remains in that shape. A row that later surfaces in a retired shape fails as
an unknown version, so the evidence for "no live rows" is what the whole call
turns on.

Two things that evidence is not. A release version is not a schema tag: the
tag a build stamps is the newest one its DTO carries, so one tag's population
spans every release between its bump and the next. And prose is not registry
state — whether a version was yanked is checkable against crates.io, npm, and
PyPI, and only those answer it.

Retirement is cheap to undo while the deleted tree is recoverable from
history. That is the argument for retiring when the evidence holds, and for
sourcing it from a row count rather than a version number.

## Gotchas

- The schema version is a hand-set constant (`STORAGE_V0_124_0`), **not**
  `CARGO_PKG_VERSION`: bumping it is a deliberate act tied to a model change.
- Unknown schema versions are rejected on read, never silently ignored.
- DTO type names carry version suffixes with underscores
  (`DocumentV0_92_0`); `non_camel_case_types` is allowed module-wide for this.
- No file extension is part of the storage contract: the interchange forms
  are card-yaml markdown **text** and `StoredDocument` **JSON**.

## Links

- [ARCHITECTURE.md](ARCHITECTURE.md): `Document` in the core type overview
- [markdown-spec.md](../references/markdown-spec.md): Markdown syntax and the in-memory data model
- [VERSIONING.md](VERSIONING.md): quill version resolution (a separate concern)
- `QuillValue` (`crates/core/src/value.rs` rustdoc): value type stored inside payload fields

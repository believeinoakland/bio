# pdf-reader — requirements

**Status** · In force: written by BOB #37 (T6), a helper module, its requirements BOB's (K20); N9's named services added by BOB (K28). D-616 does not belong here (Suggestions). Last changed T51 fix round 9 (BOB; K4831, K4834, K4837: R8, R9, R12, R22, R23, R41, R42, R43 amended; R46, R47, R48 new; marked not yet met T51). Last changed T51 (T51-7: R39 new, the document's `/Title` in `metadata`; N1202; K3627); marked not yet met (T51). Last changed T35 (T35-10: R36; K1888); every requirement met (K1920). Changed at T39's opening (N806; K2333): R37 `objects()` added for `doc-clean`.

## Public

### Purpose

Reads assembled PDF bytes — no fetch, no store, no font engine — and answers three things from them:
the document's outbound-link graph, in the same four partitions `subresources.mjs` uses for HTML, so
structure is container-agnostic; its Tier-1 text, page by page, decoded through each font's own
`/ToUnicode` map; and every image each page paints, with its rectangle. Every place it cannot resolve,
decode or classify something is named as `undetermined`, never guessed. It also exports the lenient
object/stream reader (`PdfDoc`) other Layer 1 PDF code is built on, so there is exactly one PDF parser
in the codebase.

### Provides

**extractPdfStructure(bytes) → Promise\<object\>**
- **R1** `bytes` not a `Uint8Array` → `{ ok:false, container:"pdf", reason:"NOT_BYTES" }`. No `%PDF-`
  signature in the first 1024 bytes → `{ ok:false, container:"pdf", reason:"NOT_A_PDF" }`.
- **R2** Otherwise returns `{ ok:true, container:"pdf", version, pages, links, counts, text, images,
  imagesWhy?, notes }`: `version` is the `%PDF-` header's version string; `pages` is the page count;
  `links` is the array R3-R6 describe; `counts` is R7; `text` is R11-R15's shape; `images`/`imagesWhy`
  is R16's shape, carried at the top level (not inside `text`); `notes` is a array of internal
  recovery notes (`objstm_undecodable`, `page_order_by_object_number_fallback`, `encrypted`,
  `form_stream_undecodable`, `text_extraction_error`, `content_stream_undecodable`,
  `flate_trailing_bytes:<n>`, R39's `title_undecodable`, and R8's `xref_reconstructed`, `structure_reconstructed` and `pages_missing`), present whenever
  the parser had to recover from something, informational only.
- Errors: never throws, on any byte sequence.

**Link partitions** (part of `links`, each `{ partition, wrapper, target, source }`; `source` is
`{ page, rect }` with `rect` the annotation's `/Rect` as `[x0,y0,x1,y1]` or `null` when absent/malformed;
`partition` is one of `anchor`, `intra`, `deferred`, `refused`, `undetermined`):
- **R3** An `/Annots /Subtype /Link` with `/A /S /URI` and a resolvable `/URI` string: `http`/`https`
  scheme, or no scheme at all (a bare relative reference), → `deferred`, `wrapper` = `subresources.mjs`'s
  `linkWrapper.deferred(uri)`, `target:{url:uri}`. Any other scheme (`mailto`, `javascript`, `tel`, `file`,
  …) → `refused`, `wrapper` = `linkWrapper.refused(uri)`. A URI action with no `/URI` string →
  `undetermined`, `target.why:"uri_action_without_uri"`.
- **R4** An `/A /S /GoTo` action, or a bare `/Dest` on the annotation: the destination is resolved (a
  name or string first looked up in `/Root /Dests` or `/Root /Names /Dests`, then an explicit array
  whose first element is a page reference or, for a remote/embedded go-to, a 0-based page integer) to a
  0-based target page. Resolved → `anchor`, `wrapper = linkWrapper.anchor("#page=" + (page+1))`,
  `target:{page, fragment, dest}` (`dest` is the destination's own name/string, or `null` for an
  explicit array). Not resolved → `undetermined`, `target.why` one of `dest_absent`,
  `named_dest_unresolved`, `dest_page_not_in_tree`, `dest_page_out_of_range`, `dest_first_not_page`,
  `dest_shape_unknown` (naming which step failed); `named_dest_unresolved` also carries `target.dest`,
  the unresolved name.
- **R5** A `FileAttachment` annotation, and every entry of `/Root /Names /EmbeddedFiles`: resolved to
  decodable stream bytes → `intra`, `wrapper = linkWrapper.intra(sha256Hex(bytes))`,
  `target:{sha256, name, bytes:byteLength}`. `name` is the annotation's own `/Contents` string, or the
  tree's key, or `null` — a filing label, not the address. Not resolved → `undetermined`, `target.why`
  one of `embedded_filespec_unresolved`, `embedded_stream_absent`, `embedded_stream_undecodable`, each
  carrying `target.name` when known. An annotation-sourced record's `source` is `{page, rect}`; a
  document-level (`/Names /EmbeddedFiles`) record's `source` is `null` — there is no element reference
  for it, stated rather than invented.
- **R6** A `GoToR` or `Launch` action, or a `Link` annotation with neither a recognised action nor a
  `/Dest` → `undetermined`, `target.why` = `` `unsupported_action_<S>` `` (the action's `/S` name) or
  `link_without_action_or_dest` when there is no `/S` at all.
- **R7** `counts` always carries all five keys — `anchor`, `intra`, `deferred`, `refused`,
  `undetermined` — each the number of `links` entries of that partition (0 when none).
- **R8** (fix round 9, G132b-G132f; K4834) Objects are read by the file's own structure, with a lenient scan as the fallback, and the newest revision wins. (a) The cross-reference chain from the last `startxref` (classic tables, `/Prev` links, cross-reference streams) names each object's current definition: an object an incremental update rewrites, into a new object stream included, reads as its newest definition, and `/Root`, `/Info` and `/Encrypt` are those of the newest trailer. When the chain does not validate (a bad `startxref`, a broken `/Prev`, a named object that is not there) every top-level `` `N G obj` `` is scanned instead, a later definition of one object number winning and an object-stream object counting only where no top-level definition exists, and `notes` gains `xref_reconstructed`. (b) Text inside a stream's data (an XMP packet, an attachment) is never read as an object: a `N G obj` there overrides nothing. (c) The page tree is walked from the catalog the newest trailer's `/Root` names, never the first `/Type /Catalog` in the file; a `/Kids` entry with no `/Kids` of its own is a page whether or not it states `/Type /Page`; when the walk yields no pages, every object with `/Type /Page` is used, ordered by object number, noting `page_order_by_object_number_fallback`. (d) A damaged or truncated file reads the pages it can find and states the rest: `notes` gains `structure_reconstructed` and `pages_missing`, which carries the number of pages not read and the number the file declared (a 30-page file cut at 70 percent states that 8 of 30 pages could not be read), and `ok` stays true.
- Errors: never throws.

**Tier 1 text** (`text`, part of R2's shape): `{ document, pages:[{page, text, undetermined}],
undetermined, counts:{chars, undetermined}, producer }`. `document` is every page's `text` joined by
`"\n"`, non-empty pages only. Each page's `undetermined` and the top `undetermined` are the same
markers, `{page, reason, font, codes, count}` — `codes` a hex dump of the unresolved bytes (capped at
64 bytes, `…` beyond); `count` the number of characters/codes the marker covers.
- **R9** (fix round 9, G132a, G129a; K4831 (6)) Encrypted document (the newest trailer carries an `/Encrypt` entry, as a direct dictionary or as a reference, or a `/Filter /Standard` dict with a numeric `/R` is found anywhere in the file, its own dict never itself encrypted): `text` is `{document:"", pages:[], undetermined:[{page:null,
  reason:"encrypted", font:null, codes:"", count:0}], counts:{chars:0, undetermined:1}, producer}`, with
  `producer.determination:"undetermined"`, `producer.why:"encrypted"`. No page is walked; one
  document-level marker replaces per-page ones, and ciphertext is never read as text, whichever form the `/Encrypt` entry takes. A range over such a document (R43, R44) answers the same marker with `final: true` and `count: 0`, so a caller that advances by `from + count` is told the reading ends there and is never left at the same place.
- **R10** `producer` (D-251): `{producer, creator, determination:"ocr"|"undetermined", ocr:{engine,
  field, marker}|null, why}`, read ONCE from the trailer's `/Info` — either a classic `` `trailer <<
  … /Info N 0 R >>` `` or, when there is no `trailer` keyword, an `/Type /XRef` stream's own `/Info` —
  taking the LAST candidate in file order (incremental-update semantics) and falling back to an earlier
  one when the chosen reference is dangling. `/Producer` is checked first, then `/Creator`, each against
  a fixed table of OCR-product name patterns (case-insensitive, word-anchored: ABBYY/FineReader,
  Tesseract, OmniPage, Readiris, ocrmypdf, Acrobat Capture, and the bare word "ocr"). A match →
  `determination:"ocr"`, `ocr:{engine:<the matched field's string>, field:"producer"|"creator",
  marker:<the row's own name>}`, `why:null`. No match, an empty `/Info`, a `/Producer`/`/Creator` that
  is not a string, or an unreadable `/Info` (encrypted, or a read that throws) → `determination:
  "undetermined"`, `ocr:null`, `why` one of `"no_ocr_marker_in_producer_metadata"` (a value was present
  and matched nothing), `"no_producer_metadata"` (neither field held a usable string), `"encrypted"`,
  `"info_unreadable"`. **`determination` is never `"ocr"` without a named product, and is never
  `"authored"`** — an absent or unmatched marker is an absent marker, not evidence of authorship.
- **R11** For an unencrypted document, each page's text-showing operators (`Tj`, `TJ`, `'`, `"`) are
  read from its content stream(s) (concatenated, Flate-decoded per R8's decoder) and every Form
  XObject a `Do` paints, to a nesting depth of 8 and never re-entering a form already on the walk's own
  chain (deeper or cyclic nesting: its shown-text byte count is added to an `undetermined` marker
  `form_text_unread`, page text unaffected; an undecodable form stream adds `form_stream_undecodable`
  with `count:0`). A Form XObject's own `/Resources` and `/Matrix`-composed CTM apply while it is
  painted; the page's text-state graphics parameters are restored when it returns.
- **R12** A shown byte run is decoded through the selected font's `/ToUnicode` CMap (`beginbfchar` and
  `beginbfrange`, both the incrementing and the explicit-array target forms), by the code width the
  CMap's `begincodespacerange` states, every codespace range honoured, so codes of different widths in one CMap (1 and 2 bytes: `<41814041>` reads as three characters, not two) are each read at the width their range gives, and a code is unsigned whatever its width (a 4-byte code at or above 0x80000000 maps as itself, never as a negative number) (default width when the CMap states no range: 2 bytes for a Type0/composite font, 1 otherwise). A run
  shown with no font selected → `undetermined`, `reason` `"no_current_font"` (no `Tf` yet) or
  `"font_not_in_resources"` (the selected name is not in `/Resources /Font`). A run shown by a font
  with no usable `/ToUnicode` → `undetermined`, `reason` `"cid_font_no_tounicode"` (a Type0/CID font)
  or `"no_tounicode"` (a simple font); no character is guessed. A code the CMap does not cover →
  `undetermined`, `reason:"unmapped_code"`, one marker per code. A trailing byte run shorter than the
  font's code width → `undetermined`, `reason:"code_width_misaligned"`. Every marker's `font` names the
  font's `/BaseFont` (or the resource name, or `null`) and `codes` is the undecoded bytes in hex. (fix round 9, G132g, G125f) A `bfrange` is expanded for at most `boundOf("pdf", "bfrange_codes")` codes per range (protective, proposed 65,536); a larger range is looked up arithmetically and the text is exactly what full expansion would give.
- **R13** A line break is emitted only on a change to the text LINE matrix's DEVICE-space baseline
  (`T*`, `'`, `"`, or a `Td`/`TD`/`Tm` that lands away from the line already open — never on every
  positioning operator). A positioning operator that lands ON the open baseline is judged against the
  pen's own tracked position: the pen advances by each shown character's width (a simple font's
  `/Widths`+`/FirstChar`+`/FontDescriptor /MissingWidth`, or a Type0 font's descendant CIDFont
  `/W`+`/DW`, in text space; a Type3 font's own `/FontMatrix` scale; `/Identity-H`/`-V` only for a
  composite font's code→CID map, any other `/Encoding` yielding no widths) plus `Tc`/`Tw`/`Tz`. A
  same-baseline jump beyond `0.25` em of the text it follows (magnitude, either direction) inserts one
  space; inside a `TJ` array, a forward numeric displacement beyond `0.1` em does the same (backward
  `TJ` displacements never do). **When the pen's advance cannot be established** (no font, no widths,
  an undecoded or width-misaligned run) **no gap is judged and no space is inserted** for that jump —
  the reading degrades to no break, never an invented one.
- **R14** A page with no `/Resources /Font` entry, or one whose fonts are never used by a
  text-showing operator anywhere it paints (its own streams and every form, per `pageShowsText`, R15),
  AND that declares an image XObject in its resources, carries exactly one `no_text_layer` marker (beside any R34 `image_unread` markers)
  `{page, reason:"no_text_layer", font:null, codes:"", count:0}` when it otherwise decoded to zero
  characters and zero other markers. A page that shows text, or declares no image, or whose
  text-showing status could not be determined (`pageShowsText` → `null`), never gets this marker on
  that basis alone.
- Errors: a page whose extraction throws internally is caught and recorded as `{page, reason:
  "text_extraction_error", font:null, codes:"", count:0}` for that page alone; the document-level call
  never throws.

**pageShowsText(doc, pageMap) → Promise\<boolean|null\>**
- **R15** `true` the moment any text-showing operator (`Tj`, `TJ`, `'`, `"`) runs anywhere the page
  paints — its own content stream(s) or a Form XObject it draws, to the same depth-8, no-cycle rule as
  R11. `false` only when every content stream and every form on the walk was fully decoded and read and
  none ran one. `null` — UNDETERMINED, and a caller must not read it as `false` — when any part of the
  walk could not be resolved or decoded (an unresolved `/XObject`, a form nested past the limit or in a
  cycle, an undecodable stream) before a `true` was found. `doc` is a `PdfDoc` from `openPdf` (R30);
  `pageMap` is one page's resolved dict (`pageDict`, R31).
- Errors: never throws; `pageMap` falsy → `null`.

**pdfPageImages(doc, pageIdx) → Promise\<{images, why}\>**
- **R16** `{images, why:null}`, `images` every image (an `/XObject /Subtype /Image`, or an inline
  image between `BI`/`ID` and `EI`) the page at `pageIdx` PAINTS, in painting order, each
  `{kind:"image", ref:"an image on page "+(page+1), page, rect:[x0,y0,x1,y1], mime, name, inline,
  width, height, filters, axis_aligned}`. `rect` is the axis-aligned bounding box of the unit square
  under the image's own composed CTM (`q`/`Q`/`cm`, and a Form XObject's `/Matrix`, walked the same
  way as text), rounded to 1/1000 pt, in the page's default user space — the SAME space and
  point order as an annotation's `/Rect` (R3-R6's `source.rect`). `mime` is `"image/jpeg"` for a
  `DCTDecode`-filtered stream, `"image/jp2"` for `JPXDecode`, else `null` (the bytes are samples, not
  a file); `filters` names the stream's filter chain (`[]` for an inline image). `name` is the
  XObject's resource name, or `null` for an inline image — a filing label, not the address (page+rect
  is). `axis_aligned` is `false` when the composed CTM rotates or skews the unit square. A placement
  has exactly these enumerable properties; its stream and CTM are reached only through
  `imagePlacementSource` (R32).
- **R17** `{images:null, why}` — NEVER a partial list — when any part of the page's paint sequence
  could not be walked: the page itself unreadable (`` `page_unreadable:<pageIdx>` ``), its content
  stream(s) undecodable (`` `content_stream_undecodable:page <pageIdx>` ``), a `Do` naming an
  unresolvable XObject (`` `xobject_unresolvable:page <pageIdx>:<name>` ``), a Form XObject nested past
  depth 8 or in a cycle (`` `form_nesting_unwalkable:page <pageIdx>` ``), or an undecodable Form
  XObject stream (`` `form_stream_undecodable:page <pageIdx>` ``); each string truncated to 120 chars.
- Errors: never throws (R17 is the error channel).

**Every page's images, called by `extractPdfStructure`**: `images`/`imagesWhy` on R2's top-level shape
is `null`/`"encrypted"` for an encrypted document (no page walked); otherwise every page's
`pdfPageImages` result concatenated in page order, or the FIRST page's `why` (R17) the moment one page
cannot be walked — the same never-partial rule as R17, for the whole document.

**openPdf(bytes) → Promise\<PdfDoc|null\>**
- **R30** Returns a `PdfDoc` over `bytes` that has run R8's whole lenient read (top-level scan, object
  streams, page index), exactly as `extractPdfStructure` opens its own document, ready for every
  service below. `bytes` not a `Uint8Array`, or no `%PDF-` signature in the first 1024 bytes → `null`.
- Errors: never throws.

**imagePlacementSource(placement) → {stream, ctm} | null**
- **R32** For a placement `pdfPageImages` returned: `stream`, the image XObject's stream value (readable
  with `resolve`, `streamRawBytes`, `streamDecoded`), or `null` for an inline image; `ctm`, a fresh copy
  of the six-number composed CTM `[a,b,c,d,e,f]` its `rect` was computed from (R16). Anything else,
  a copy of a placement included → `null`.
- Errors: never throws.

**PdfDoc** — the shared lenient PDF object/stream reader. `pdf-pixels` drives it through `openPdf`. Its
interface is the members below and nothing else; every other field is private.
- **R18** `new PdfDoc(bytes)` holds the bytes; `scanTopLevel()`, `await loadObjectStreams()` and
  `buildPageIndex()` perform R8's three steps in that order (`openPdf` runs all three).
- **R19** `.pageCount` is the number of pages in R8's page order once `buildPageIndex()` has run; `0`
  before it runs or when the document has no pages.
- **R31** `pageDict(pageIdx)` returns the resolved dict (`map`) of the page at 0-based `pageIdx` in page
  order; `null` when `pageIdx` is not an integer in `[0, pageCount)` or the page object is unresolvable.
  Its result is a valid `pageMap` for `pageShowsText` (R15).
- **R38** (T40; N813, K2351, K2390) A string value the reader answers is `{t:"str", v, raw}`: `raw` is the string's bytes exactly as the file states them (a literal's escapes and a hex string's digits decoded, an odd final hex digit read as followed by 0, per the PDF syntax), as a `Uint8Array`; `v` is its text, UTF-16BE decoded after the `FE FF` mark when `raw` begins with it, otherwise each byte as one code unit. A caller that writes a string back writes `raw`, so no string, binary or odd-length, loses or changes a byte.
- **R20** `resolve(v)` follows an indirect-reference chain (`{t:"ref", n, g}`) up to 64 hops and
  returns the resolved value, or `null` for an unresolvable reference, a reference cycle beyond the cap,
  or a non-reference value passed through unchanged.
- **R21** `dictOf(v)` resolves `v` and returns its `dict`/`stream`'s `map`, or `null` for anything else
  (including an unresolvable reference).
- **R22** `streamRawBytes(streamObj)` returns a stream value's raw (still-filtered) bytes: by its
  resolved `/Length` when that agrees with an `endstream` at or just after the implied end, otherwise by
  scanning forward to the next `endstream` (trailing EOL excluded). Returns `null` for a non-stream
  value or when no `endstream` is found.
  `streamDecoded(streamObj)` returns the stream's raw bytes unchanged when it carries no `/Filter`;
  Flate-decoded (native `DecompressionStream("deflate")`, falling back to `"deflate-raw"` for a raw
  deflate stream with no zlib header) and PNG-un-predicted per `/DecodeParms /Predictor` (≥10; the
  `/Colors`, `/Columns`, `/BitsPerComponent` it names, defaulting 1/1/8) when every filter in the chain
  is `FlateDecode`/`Fl`; `null` for any other filter, an unreadable stream, or a decode failure — the
  caller treats `null` as "cannot resolve," never as empty bytes. `streamDecoded` is asynchronous: it answers a Promise of those bytes or `null`, and never rejects (T40; N813, K2390).
  (fix round 9, G125a, G125e, G132l (a); K4831 (8), K4834) **Streams are bounded before they are held.** A Flate stream is inflated streaming against a cap by its kind, never whole first: a page's content `boundOf("pdf", "page_content")` (protective, proposed 64 MiB decoded), an object stream (`"object_stream"`, 16 MiB), a ToUnicode CMap (`"cmap"`, 1 MiB), an embedded file (`"embedded_file"`, 64 MiB, hashed as it streams, never held). A stream that passes its cap is stopped there: `streamDecoded` answers `null` (cannot resolve), and the reader states it with the stream's size and the bound, as `page_over_bound` for a page (R41) and as a `notes` entry `stream_over_bound:<kind>` for the others; a stream under 128 KiB compressed is held to the same cap, not exempt. An image stream's declared `/Width`, `/Height`, components, bits and a predictor's row length are judged against `boundOf("image", "pixels")` and `boundOf("image", "row_stride")` before anything is allocated for it (a 97 KB Flate stream declaring 10000 x 10000 grey is not inflated): a breach is `null` with the note `stream_over_bound:image`, and `pdf-pixels` states `IMAGE_TOO_LARGE` from the same declared size. A stream with a TIFF predictor (`/Predictor 2`) is not passed through as if un-predicted: `streamDecoded` answers `null`, so a caller states the pixels undetermined.
- **R23** `isEncrypted()` reports whether any object in the file carries `/Filter /Standard` with a
  numeric `/R` (the Standard Security Handler dictionary, which the standard requires stay
  unencrypted); cached after the first call. (fix round 9, G132a) It also reports `true` when the newest trailer carries an `/Encrypt` entry, direct or by reference (R9).
- **R37** (T39; N806; K2333) `objects()` answers `{trailer, objects, unresolved}` for the latest revision: `trailer` the resolved dict of the last trailer in file order (a classic `trailer` dict, or an `/Type /XRef` stream's own dict, as R10 chooses it); `objects` every indirect object reachable from it (by any chain of references from its entries), each once, as `{num, gen, value}` in ascending `num`, `value` as `resolve` (R20) answers it, an object from an object stream included as any other; `unresolved` each reference on those chains that cannot be resolved, as `{num, gen}`, `[]` when none. `null` when no trailer can be read. Never throws.
- Errors: no `PdfDoc` method throws on malformed input; a read that cannot resolve returns `null`,
  `false`, or an empty result, per the method's own rule above.

- **R39** (T51; N1202; K3627; amends R2) R2's answer carries a top-level `metadata` (beside `images`, so tier 2's replacement of `text` keeps it): `{title?, source: "/Info"}`, where `title` is the document's `/Title` from the same `/Info` dictionary R10 chooses, decoded as a PDF text string from its raw bytes (R38): UTF-16BE when they begin with `FE FF` (the mark dropped, any language-tag escape skipped), otherwise PDFDocEncoding. `title` is present only when the decoded text is not empty and not only whitespace; with an absent `/Title`, a `/Title` that is not a string, an empty or whitespace-only one, `metadata` has no `title` key (never `null`, never invented from the file name or a heading). A title that cannot be decoded (an odd-length or unpaired-surrogate UTF-16BE string, a byte PDFDocEncoding leaves undefined) is stated as no `title` and `notes` gains `title_undecodable`; no character is replaced or guessed. `metadata` is `null` when no `/Info` dictionary can be read (none, dangling, or an encrypted document, R9, whose strings are not decoded). Test: hand-built PDFs whose `/Info` states `/Title (Housing Notice)`, a UTF-16BE `<FEFF…>` title with a non-ASCII letter, and a PDFDocEncoding byte above 0x7F (such as `•` at 0x80) read each exactly; control: no `/Title`, `/Title ()`, `/Title (   )`, `/Title 12`, an odd-length UTF-16BE title (no key, `title_undecodable`), no `/Info` and an encrypted fixture (`metadata: null`).
- **R33** (D-374, N100; K279) R2's answer carries a top-level `pageBoxes` (beside `images`, so tier 2's replacement of `text` keeps it): `{boxes: [{media_box: [x0, y0, x1, y1], w, h, rotate}], of_page: [index | null]}`, `of_page[i]` indexing page i's distinct box in `boxes` (each distinct box stored once), or `null` where that page's box cannot be read. The box is the page's /MediaBox, inherited up the page tree, corners normalised, origin kept (never re-based to 0,0), never a default; four finite numbers with positive area, else `null`. `rotate` is the inherited /Rotate normalised to 0/90/180/270, 0 when absent, `null` when not a multiple of 90; it does not move the box. `pageBoxes` is `null` only when the document has no pages. Boxes are read for an encrypted document too.
- **R34** (D-665, N101; K279) With `images` a list, every placement whose rect covers at least 0.001 of its page's visible box (R26's box), or whose page box cannot be read, adds to its page's `undetermined`, in painting order and after any R26 marker, `{page, reason: "image_unread", font: null, codes: "", count: 0, rect, area_share}`: `rect` exactly the placement's, `area_share` the rect clipped to the box over the box's area, to 4 places, `null` without a box. It routes nothing, and is carried on a `no_text_layer` page too (R14).
- **R35** (REC-206, N101; K279) Every `links[]` record carries `anchor: {text, why, tier: 1}`: the text tier 1 shows whose glyph ink point (mid-advance, 0.35 em above the baseline, default user space) lies in the link's `source.rect`, in showing order, runs joined by one space, whitespace collapsed, trimmed. `why` is `null` only for a complete reading, else one of `no_rect`, `text_not_read`, `no_text_in_rect`, `positions_unknown`, `partly_unplaced`, `undecodable`, `partly_undecodable` (REC-206's meanings). R3–R6's exact records gain the `anchor` key.
- **R36** (K1888) R2's answer carries a top-level `active` (beside `images`, so tier 2's replacement of `text` keeps it): every place the file can act when it is opened, found and read, never executed. One item `{kind, where, detail}` per finding, in object-number order and, within one object, in key order. `kind` is one of: `open-action` (the catalog's `/OpenAction`; `detail` the action's `/S`, or `"destination"` for a bare destination); `additional-actions` (an `/AA` dictionary on the catalog, a page, an annotation or a form field; `detail` its trigger keys as written, such as `["/O"]`); `javascript` (a `/JS` key, an action whose `/S` is `/JavaScript`, or the catalog's `/Names /JavaScript` tree); `xfa` (`/AcroForm /XFA`); `rich-media` (an annotation of `/Subtype /RichMedia`, or a `/RichMediaContent` key); `launch` (an action whose `/S` is `/Launch`, R6); `embedded-file` (each R5 record, `intra` or `undetermined`; `detail` its `name`); `encryption` (the Standard security handler, R9, R23; `detail` its `/R`). `where` is `{object, page, key}`: the number of the indirect object holding the finding (`null` for one with none), the 0-based page when that object is a page or an annotation of one (`null` otherwise), and the key that holds it. Names are compared after their `#xx` escapes are decoded (`/J#61vaScript` is `/JavaScript`), and every object R8's read reaches is examined, in the page tree or not. Where part of the file could not be read, the list carries `{kind:"unread", where:null, detail}`, `detail` `objstm_undecodable` or `encrypted` (an encrypted document's object streams are not decoded; its unencrypted dictionaries are still examined): the list MAY be missing items, stated, never read as none. `active` is `[]` only when nothing was found and nothing went unread. An item says the file can act, never that it is malicious.
- **R40** (fix round 4, C25; K4429; `acquisition` R98) `pdfTitle(bytes) → string | null` reads only the document's Info `Title` entry and, failing that, its XMP `dc:title`, without reading any page, within 100 ms for a file of 16 MB, and answers the title uncleaned (the caller cleans it), or `null` for none, an encrypted file's title it cannot read, or bytes that are not a PDF; it never throws. Test: the IRS Form 1040-ES, a PDF with an XMP title only, and a PDF with none answer the title, the XMP title and `null`; the 15.9 MB `BUDGET-2024-APP.pdf` answers inside 100 ms. Control: `extractPdfStructure` is unchanged.
- **R41** (fix round 4, C5a/P8; K4434; EXTRACTION #30 J8's measurement: +136/+318/+386 MB over the idle isolate for the 2.39/8.39/15.19 MiB govinfo PDFs) **The reading of a PDF is bounded in memory.** `extractPdfStructure` (and every reader of this module a reading calls) holds at most one page's decoded content at a time, plus the cross-reference and the objects that page needs, and drops each page's decoded streams once its text is taken; for a PDF of up to 16 MB its peak memory above the isolate's idle is under 64 MB, whatever its page count, and its answer is the same as before, unit for unit. Test, on the real govinfo files `BUDGET-2025-BUD.pdf`, `BUDGET-2025-PER.pdf` and `BUDGET-2024-APP.pdf` (saved as fixtures or fetched once into the job's cache): peak heap plus array buffers above the baseline stays under 64 MB each, measured red first; the extracted structure equals today's for each. Control: a small PDF's answer is unchanged. (fix round 9, G124d, G125e; K4831 (8)) **A page whose decoded content passes the page bound is stated, not held.** A page whose decoded content passes `boundOf("pdf", "page_content")` (R22) is not held: it carries the page marker `{page, reason:"page_over_bound", font:null, codes:"", count:0, size, bound}` with its figures, every other page is read as before and the call ends with the process alive (a 3 MB decoded page under a 128 MB heap; 1,000 light pages and one 40 MiB page; a 201 KB file whose page 3 inflates to 200 MB reads pages 1-2 and 4-10).
- **R42** (fix round 4b, F10; K4498, K4504) **A document too large to read is refused before its text.** Before any page's text is built, `extractPdfStructure` refuses a PDF whose reading would not fit the object: need (MB) = 25 + the file's MiB + pages × (0.006 + 0.025 × the share of pages that show text); over 100 it answers `{ok: false, container: "pdf", reason: "TOO_LARGE_TO_READ", failure: "final", version, pages, bytes, need_mb, limit_mb, text_share}`, with no text and no links. The share is counted as 1 unless the rule with 1 is over 100, and then it is the share of 16 evenly spaced pages that show text (a page that cannot be told counts as text; an encrypted file counts 0); the sample leaves the document's notes as they were. Test (`refusal.test.mjs`): a 3,500-page text-dense file under 24 MiB is refused with its pages in under 64 MB above idle; 2,300 text pages are read and 2,450 refused; 3,500 scanned pages under 24 MiB, 3,500 encrypted pages, the 20 MB 1,300-page synthetic and BUDGET-2024-APP are read with their answers unchanged. (T51 fix round 5, E2; K4542) A second term refuses a reading whose pages carry more text than the page rule was measured on: for a document of more than 64 pages that the first term passes (not encrypted), 16 evenly spaced pages are read as the reading reads them, their notes left as they were, and need (MB) = 29 + the file's MiB + 0.001 × pages + 1.8 × the million characters (decoded characters and undecodable codes) they show, scaled to all the pages; a document whose need on either term is over 100 is answered as above. Test (`density.test.mjs`): 1,500 pages of 200 lines (11.6 MB) are refused with their pages and `need_mb` between 100 and 125; 1,000 pages of 120 lines are read; 3,000 pages of 80 lines are refused by the first term; the first term's tests stand. (fix round 9, G124a; K4835 (1)) The figure 100 in `need`'s limit is quoted from `READ_BOUNDS` (`boundOf("pdf", "need_mb")`, the alpha column, today's 100) with no numeric literal of its own, and the refusal is a stated, final one, never `transient`, carrying `need_mb` and `limit_mb` as the member's sentence's size and limit (K4831 (3)).
- **R43** (fix round 6, G26; K4606, K4608) **A PDF can be read by page ranges.** `extractPdfRange(bytes, {from, count})` opens the document once per call and answers `{ok: true, container: "pdf", pages: <total>, from, count: <pages built>, text: {pages: [{page, text, undetermined}], undetermined, counts}}` for the pages `[from, from + count)` (0-based, `count` clamped to the pages left), in the shape of the whole reading's `text` for those pages, with R26's and R34's image markers; a `from` at or past the end answers `count: 0` and no pages; non-bytes, not a PDF and an encrypted document answer as `extractPdfStructure` does; no R42 refusal. The union of ranges over a document is the whole reading's pages, each once. A range of 100 pages of a 15.2 MiB, 1,354-page volume completes in a V8 old space of 25 MB beside its bytes. Test: `range.test.mjs`; platform check `workerd-range.probe.mjs`. (G56, K4705) `range.maxBytes`, when a finite number above 0, bounds the pages built: at most `max(1, floor(maxBytes / (bytes.length / pages)))`; it only shrinks the pages asked, builds at least one page when any is left, and absent (or not a finite number above 0) the call is as without it. Test: `range.test.mjs`. (fix round 9, G124d, G129a; K4831 (6)) `maxBytes` is judged against each page's own decoded size as the page is built, not the document's average: the range stops before the page that would pass `maxBytes` (after at least one page), so a heavy page among light ones is a range of its own and is stated under R41 if it passes the page bound. A range over an encrypted document answers R9's marker with `final: true`.
- **R44** (fix round 7, G68; K4738) **A PDF parsed once, read by ranges many times.** `openPdfRange(bytes)` parses the document once and answers `{ok: true, pages: <total>, range({from, count, maxBytes})}`, or the same refusal `extractPdfRange` gives for those bytes; each `range(...)` call answers exactly what `extractPdfRange(bytes, {from, count, maxBytes})` answers for the same arguments (R43), and no `range` call scans or decompresses the file again. The opened document holds no more memory than one `extractPdfRange` call's parse.
- **R45** (fix round 7, G82; K4743) **Opening a PDF yields.** `openPdfRange(bytes, {yieldNow})`: when `yieldNow` is a function, the open awaits `yieldNow()` between its phases (the object scan, the object streams, the page index) and within any phase whose work grows with the file, so no synchronous stretch of the open exceeds what one phase step does on a bounded slice; its answer and every `range` answer are identical to the call without `yieldNow`. Without `yieldNow` it behaves as R44. **Amended (fix round 9, G179; K5006):** the text entry yields the same way within its compute over a region (each loop whose work grows with the region awaits `yieldNow()` on a bounded slice), so a reading tick holds the thread no longer than one slice. Test: reading-pipeline's `r7-contention` with its same-run control: a cheap request beside the 21 MB PDF's ticks waits at most 150 ms times `slow`, five of five under four CPU burners. *(not yet met: T51)*
- **R46** (fix round 9, G128c; N3; K4834) **A range carries what the whole reading stores.** Every `range(...)` answer (R43, R44) also carries the document-level members of R2's answer that a reading stores, in their own members and not inside `text`: `metadata` (R39) and `pageBoxes` (R33) of the whole document, the `images` (R16) placed on the pages of the range, and for those pages their glyph and word counts (`text_glyphs`, `words_total`). The union of a document's range answers equals the whole reading's `metadata`, `pageBoxes`, `images` and counts, for every file (a title, a page box and an image rect are never lost because the first range was the only one asked).
- **R49** (fix round 9, G132k; K4859; for pdf-pixels R47) **One page from a range source.** `pageSource(source, pageIndex) -> Promise<{ok: true, pages, bytes} | {ok: false, fallback: true, why}>` over `source = {size, readRange(offset, length)}`: `bytes` is a self-contained PDF holding that one page (its inherited `MediaBox`, `Rotate` and `Resources` written into its page dictionary; its contents, resources and image streams), assembled from the trailer, the cross-reference chain (tables, streams, object streams) and the page tree read through `readRange` alone, so the bytes read are bounded by that page and not by the file; the page renders and reads as the same page of the whole file does. No usable cross-reference, an `/Encrypt` trailer, an index out of range or a damaged object answers `{ok: false, fallback: true, why}`; it never throws, and the caller then reads the whole file.
- **R47** (fix round 9, G124, G125; K4831 (8); section 2b ruling (1)) **Protective limits, stated and never a crash.** The module holds these ceilings, each quoted from `READ_BOUNDS` (the protective column; the figures are proposed and BOB records them): objects retained 2,000,000; a direct object 4 MiB and 65,536 operands; page-tree depth 256; and R22's and R12's stream, CMap and `bfrange` bounds. A file past one is stated as a deterministic refusal or a marker naming the bound, its figure and the size found, never read on without the bound and never `transient`; an input made to pass a bound (a tree 1,000 deep, 3,000,000 objects) leaves the process alive and the answer within the bound.

## Private

### Uses

- `runtime-limits`: `READ_BOUNDS` and `boundOf(kind, name)` for every ceiling this module keeps (R22, R41, R42, R47, R48).
- `subresources`: `LINK_TYPES` (the four HTML link partitions: `anchor`, `intra`, `deferred`,
  `refused`) and `linkWrapper` (`.anchor`/`.intra`/`.deferred`/`.refused`, each a wrapper constructor)
  — reused, never re-derived, so a PDF link and an HTML link of the same partition carry byte-identical
  wrappers (R3-R5).

### Invariants

- **R24** Pure: no store read or write, no network call, no clock. `extractPdfStructure`,
  `pageShowsText` and `pdfPageImages` answer only from their input bytes/`PdfDoc`, so the same input
  always gives the same output.
- **R25** A Flate-compressed stream with bytes after the compressed data's own
  end still decodes: the decoded bytes are kept, and `notes` gains `flate_trailing_bytes:<n>` once per such
  stream. A page whose content stream cannot be decoded carries the page marker `{page,
  reason:"content_stream_undecodable", font:null, codes:"", count:0}`, and one whose `/Contents`
  resolves to nothing carries `reason:"content_stream_unresolvable"`; neither reads as a blank page.
- **R26** A page's image share is the area its painted images (R16) cover,
  as a share of its visible page box; its glyphs are the characters it shows (R11-R12). A page with
  at most 4 glyphs and an image share of at least 0.18 carries the marker `image_content_unread`. Any
  other page that paints an image and shows fewer than 22 glyphs (a share under 0.18, 5-21 glyphs, or a
  page box that cannot be read) carries `image_content_undetermined`. A page that paints no image, or
  shows 22 or more glyphs, carries neither. Both markers name
  `image_share` and `glyphs`. R26 applies only to a page that shows text: a page carrying `no_text_layer`
  (R14) carries neither R26 marker. The figures are measured
  (M-178: 1,788 pages; the 17 image-only pages show at most 4 glyphs at shares 0.1897-0.6542; every
  other page painting an image shows at least 22 glyphs).
- **R27** Every `undetermined`/`why`/`reason` value in this module's output names WHICH kind of
  unresolved thing it is (a missing font, an unresolved destination, an unwalkable form, an unreadable
  `/Info`, …); none is a bare `false`/empty result standing for every cause at once, and a decode
  failure is never silently read as "nothing there."
- **R28** `producer.determination` (R10) has exactly two members, `"ocr"` and `"undetermined"`; a
  classification can only ever add a named engine to a document that had none, never remove one or
  invent authorship. `text` never carries a producer claim stronger than what the file's own bytes
  state.
- **R29** No place is named in this module's logic: `WORD_GAP_EM` (0.25), `TJ_WORD_GAP_EM` (0.1), the
  Form nesting depth (8), and the OCR product-name table are general PDF-reading parameters, not
  jurisdiction facts, even where a comment cites an Oakland/Legistar document as the measurement that
  set one — the tests use fixtures built by hand, not any one jurisdiction's documents, and the module
  needs no jurisdiction profile (`build/layers.md`, "No jurisdiction in the product").
- **R48** (fix round 9, G124; K4835 (1)) No numeric literal in this module's code is a ceiling it keeps: each ceiling it enforces (R12, R22, R41, R42, R47) is read from `READ_BOUNDS` (`boundOf`), and a test reads this module's `src` and finds none.

### Satisfies

- `BIO_Content_Framework_v0_10.md` §16, "How content is extracted today" — the PDF read path: Tier 1
  here, Tier 2/3 escalation this module's `no_text_layer`/`producer` signals drive but do not perform.
- `docs/development/EXTRACTION-BREADTH-DESIGN.md` §3, "Tables and images as content" (R16-R17, the
  IC-1 `image` reference this module mints) and §6, "The external OCR tier" (R10's producer signal is
  that routing's input).
- `BIO_Interaction_Constructs_v0_1.md` §U, "UNDETERMINED — a display primitive, not an act" — the
  doctrine R27 states as an invariant of this module's whole output.
- `build/layers.md`, "No jurisdiction in the product" (R29).
- Bob's K1888 (2026-10-06, the virus package: the readers' structure check; `build/plan/study-virus-scanning.md` §3 A, after PDFiD's triage keys): R36.
- Bob's K2315 (N806, packaged by BOB's K2333: a member document's embedded images leave without their metadata): R37, the object walk `doc-clean`'s rewrite of a PDF reads.
- Bob's K4831 (3), (6), (8) and K4834 (the alpha's stated limits; password files stated; protective limits), K4835 (1) (the table in `runtime-limits`): R8, R9, R22, R41-R43, R46-R48.

### Suggestions

- **D-616 does not belong to this module.** Its fix — seeding a re-read (`op=pdfstructure&ocr=1`) with
  the pages a stored reading already transcribed, so a later request advances past the per-request OCR
  budget instead of re-asking the same first pages — reads and mutates the stored reading, which a
  Layer 1 "no access to the record" module cannot do. `tier3Extend`/`needsTier3` are defined in
  `bio-plane/src/index.mjs` today; the row belongs against whichever module ends up owning that
  read-time orchestration (`index.mjs`'s extraction, when it is extracted) or `pdf-worker`, not here.
- The existing hand-built PDF fixtures in `bio-plane/test/pdfstructure.test.mjs` (and the sibling
  `cpdf18-pdf-images.test.mjs`, `d608-form-text.test.mjs`, `producer-provenance.test.mjs`,
  `textshown.test.mjs`) already cover most of R1-R24 byte-for-byte; R25/R26's tests want a fixture with
  a deliberately trailing-junk Flate stream and, once D-627's thresholds are measured, a fixture whose
  image share and glyph count straddle them.
- No entry in `bio-plane/checks/bio-checks.mjs` is owned by this module today (searched for every
  exported name and found none): `pdf-reader` imports no `legacy-checks` service and nothing in the
  catalogue calls its functions directly, so there is no C-number invariant to carry forward here.
- R36's `active` is the PDF half of the per-capture "active content" list (the office half is
  `office-readers` R32); the threat grade, the members' warning and the assistant's rule read it
  downstream (K1888). PDFiD (Didier Stevens) over the same fixtures is a fair oracle for the
  counts of `/OpenAction`, `/AA`, `/JS`, `/JavaScript`, `/XFA`, `/RichMedia`, `/Launch` and
  `/EmbeddedFile`, obfuscated names included.

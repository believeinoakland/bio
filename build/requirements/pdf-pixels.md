# pdf-pixels — requirements

## Public

### Purpose

A PDF page, an image a page places, or a picture file (R42), as upright PNG pixels: page analysis, filter chains and routes,
rotation, PNG, and crop, with their declared refusal vocabularies (`REFUSALS`, `CROP_REFUSALS`). Tier 3
(`ocr-worker`) and `content` read through it. It writes nothing and holds no binding.

### Provides

**`renderPageToPixels(bytes, pageIndex, opts={}) → {ok:true, …} | {ok:false, reason, why, …}`** —
exported from `pagepixels.mjs`; the function `ocr-worker` imports directly (never over HTTP).
- **R13** `bytes` must carry a `%PDF-` header in its first 1024 bytes, else `NOT_A_PDF`.
- **R14** An encrypted document answers `ENCRYPTED`.
- **R15** `pageIndex` outside `[0, pageCount)` answers `NO_SUCH_PAGE` with `pageCount`; a page object
  that cannot be read (in range) answers `PAGE_UNREADABLE`.
- **R16** A page that SHOWS text — `pdf-reader.pageShowsText`: a text-showing operator (`Tj`, `TJ`, `'`,
  `"`) runs in its content or in a Form XObject it draws; a bare `BT` is not text (D-585) — answers
  `PAGE_HAS_TEXT_LAYER` with `imageCount`, unless `opts.allowTextPage` is true.
- **R17** A page that paints no image (`pdf-reader.pdfPageImages`) answers `NO_IMAGE_ON_PAGE` when it also paints no vector mark
  (a fill, stroke or shading operator; a clip alone does not count), else `NOT_IMAGE_ONLY`.
- **R18** A page painting more than one image (counted from what it paints, `pdf-reader.pdfPageImages`,
  never from the image XObjects its `/Resources` lists) answers `MULTIPLE_IMAGES_ON_PAGE`, with every image's
  `{width, height, filters}`; images are never composited.
- **R19** The one remaining image is decoded per R22–R25; its own refusal, if any, is returned with
  `page` added.
- **R20** On success: `{ok:true, page, route, mediaType, bytes, width, height, upright, rotate_deg,
  source:{filters, colorSpace, bitsPerComponent, imageMask}, page_geometry:{mediaBoxPt, rotate, dpi},
  page_marks:{hasTextOps, hasVectorOps}, turned_deg (R48), …(ccitt|dct detail when decoded), …(pixels_sha256 when
  decoded)}`. Its success `detail` also covers `jbig2` and `jpx` beside `ccitt` and `dct` (K54).
- **R21** `rotate_deg` and the rotation applied to the pixels are the page's `/Rotate`, an inheritable
  attribute: the page's own value, else the nearest `/Parent` ancestor's, else 0; normalised to 0/90/180/270.
  A `/Rotate` that is not a multiple of 90 answers `PAGE_UNREADABLE` (R15), never a guessed turn.
  `opts.rotate`, if given, is ignored — the page's value always wins.

**Decode rules**, shared by `renderPageToPixels` and `cropImage` (`decodeImage`):
- **R22** DCTDecode (the stream IS a JPEG), filter chain of length 1: by default passed through
  untouched — `route:"passthrough-dct"`, the publisher's own bytes, `upright` true only when the
  rotation is 0. With `opts.decodeDct` (only `renderPageToPixels` exposes this): decoded to an 8-bit PNG by
  `image-codecs`' JPEG decoder (its R1) — `route:"decoded-dct"`, rotated, `upright:true`, carrying `dct` detail and
  `pixels_sha256`. Refused `UNSUPPORTED_JPEG_PROCESS` (not baseline/extended-sequential Huffman, 8-bit);
  `UNSUPPORTED_SAMPLES` (a `/Decode` array on the image, a component count or sampling ratio the SOF
  marker does not support, or a `/ColorTransform` the file's own markers contradict); `TRUNCATED_IMAGE_
  DATA`; or `DECODE_FAILED`, as the bytes require. A filter chain with anything before `DCTDecode`
  answers `UNSUPPORTED_FILTER`. (Fix round 9, G132l (b)) The pass-through is not unexamined: the stream's own JPEG header is read first, and it must agree with the image dictionary (width, height, component count); a stream whose header cannot be read, or disagrees, answers `PIXELS_UNDETERMINED` (R45) in place of the publisher's bytes presented as the page.
- **R23** CCITTFaxDecode: decoded G3 (K=0) or G4 (K<0) by `image-codecs`' `ccittDecode` (its R2) to a 1-bit PNG, rotated exactly (a bit lands on a
  bit), `upright:true`, carrying `ccitt` detail and `pixels_sha256`. The filter immediately before it may
  only be `FlateDecode` (decoded first); any other predecessor, or mixed mode (K>0, refused because a
  stream with no EOL gives no way to read the per-row mode bit), answers `UNSUPPORTED_FILTER`. Fewer rows
  decoded than the image's declared height answers `TRUNCATED_IMAGE_DATA`; an unreadable stream answers
  `IMAGE_UNREADABLE`. (Fix round 9, G132l (b)) A `/Columns` that is not the image's `/Width` answers `PIXELS_UNDETERMINED` (R45), not a silently mis-sized bitmap.
- **R24** No filter, or `FlateDecode` alone: 1-bit samples (an `/ImageMask` or 1-bpc grey) or 8-bit
  samples (grey or RGB) are copied/rotated to a PNG the same way, `upright:true`, carrying
  `pixels_sha256` on the 8-bit route. Any other colour-space/bit-depth combination (CMYK, 16-bit, …)
  answers `UNSUPPORTED_SAMPLES`; data short of the declared height answers `TRUNCATED_IMAGE_DATA`; a
  missing width/height or unreadable stream answers `IMAGE_UNREADABLE`. For an `/ImageMask`, a sample 0 paints and a sample 1 leaves the page unpainted under the default `/Decode` (PDF §8.9.6.2; K54). (Fix round 9, G132l (a), (b)) A `/Decode` array that is not the default (`[1 0]` inverting a sample), an `/SMask` or a `/Mask` on the image (whose alpha or colour key the pixels would ignore), and a TIFF predictor (`/Predictor 2`, which `pdf-reader` R22 does not undo) answer `PIXELS_UNDETERMINED` (R45); the pixels are never `ok:true` and wrong.
- **R25** A `JBIG2Decode` image (with its `JBIG2Globals`) and a `JPXDecode` image are decoded by
  `image-codecs` (its R3, R4) to a PNG like R23 and R24, carrying `pixels_sha256`. A codec's refusal
  answers `UNSUPPORTED_FILTER`, naming the feature (for JBIG2, the segment type), or the `REFUSALS` reason
  this module maps that refusal key to; the mapping is total over `JBIG2_REFUSES` and `JPX_REFUSES`.
  A codec's `IMAGE_TOO_LARGE` refusal (`image-codecs` R12; the JPX memory bound, N34, is one) maps to `IMAGE_TOO_LARGE` ("decoding the image would need more memory
  than a decode may use here"), carrying the codec's feature and figures in its detail (K116). (Fix round 9, G132l (d)) A JBIG2 region taller than its data answers the reason its short-data refusal maps to (`TRUNCATED_IMAGE_DATA`), never rows invented to fill it.
- **R26** A route that DECODES samples (R23, R24, or R22 with `decodeDct`) carries `pixels_sha256`, a
  SHA-256 over the normalised packed/interleaved samples taken before any container is built; a
  pass-through route (R22 default) carries none, its bytes being the publisher's own and byte-stable by
  definition.

**`cropImage(bytes, extent) → {ok:true, derived:true, …} | {ok:false, derived:true, reason, why, …}`** —
exported from `imagecrop.mjs`. Fully built and tested; **no production caller reaches it today** — see
Status.
- **R27** `extent` must be `{kind:"image", page:<integer>, rect:[x0,y0,x1,y1]}`, four finite numbers, no
  `part`; else `NOT_AN_IMAGE_EXTENT` (wrong kind, or `page` not an integer, or `part` given) or
  `RECT_REQUIRED` (rect missing or malformed — a page alone names no one image to crop).
- **R28** `NOT_A_PDF`, `ENCRYPTED`, `NO_SUCH_PAGE` as R13/R14/R15.
- **R29** When the page's paint order cannot be walked, `PAGE_UNWALKABLE` carrying `pdf-reader.
  pdfPageImages`'s own `why`.
- **R30** The rect is matched, within 0.001 pt after normalising (`x0<x1`, `y0<y1`), against every image
  the page paints. No match: `NO_IMAGE_AT_RECT` with every rect the page did paint. More than one match:
  `AMBIGUOUS_RECT` with the count. A match that is an inline image: `INLINE_IMAGE`.
- **R31** The matched image is decoded per R22–R25 with rotation forced to 0 (a crop is never turned); a
  decode refusal answers `DECODE_REFUSED` naming the decoder's own `reason` and `why`.
- **R32** On success: `{ok:true, derived:true, rendition:"crop", why, of:{kind:"image", page, rect},
  capture_sha256, placement:{name, axis_aligned, filters}, route, mediaType, bytes, width, height,
  upright, file_sha256, pixels_sha256?}`. `capture_sha256` (of the whole capture) and `file_sha256` (of
  the returned crop bytes) are always present; `pixels_sha256` only on a decoded route.
- **R33** `upright` is `true` only when the placement's matrix is a plain positive scale-and-translate (no
  rotation, skew or flip) AND the decoder itself reports upright samples; otherwise `null` — never
  guessed.
- **R34** Never composites marks drawn over the image and never applies the placement's own rotation or
  flip: the crop is the image exactly as the file stores it (EXTRACTION-BREADTH §3.4).

**A picture file** (T43; N853b; K2611, K2691):
- **R42** `renderPictureToPixels(bytes, pageIndex, {maxEdge, grey})` (`picturepixels.mjs`) answers `{ok: true, page: 0, route: "decoded-picture", mediaType: "image/png", bytes, width, height, upright: true, orientation, reduced_by, source: {format, width, height, comps}, pixels_sha256}` or `{ok: false, reason, why, …}`. Refusals: bytes neither JPEG nor PNG, `NOT_A_PICTURE`; `pageIndex` not 0, `NO_SUCH_PAGE` (`pageCount: 1`); `width × height × components` from the header over the exported `PICTURE_FRAME_MAX` (measured by the job), or either side over `boundOf("image", "edge")` (protective, 65,535), `IMAGE_TOO_LARGE`, before any decode; a codec's refusal mapped as R22 and R25 map them, total over `PNG_REFUSES`. Otherwise it decodes (`image-codecs` R1, R10), orients (R43), turns grey when `grey`, reduces by the smallest integer factor bringing the long edge to `maxEdge` or less (a box average; partial edge boxes over the pixels present), and encodes an 8-bit PNG, pixel-exact against Pillow (`exif_transpose`, `convert("L")`, `reduce(k)`). It never answers the file's own bytes. (T44; N868; K2701, K2702) A JPEG is decoded while it is reduced: read through `image-codecs` R11, each strip turned grey when `grey` and summed into the boxes of the reduced picture, so the full-size frame is never held. The boxes are those of this reduction of the oriented picture, R43's orientation applied as the boxes are mapped back to the source, so partial edge boxes fall where Pillow's fall; the answer is unchanged (pixel-exact against Pillow over the full decode). `PICTURE_FRAME_MAX` then applies to the reduced frame, `ceil(width/k) × ceil(height/k) × components`; the header's full frame is judged against a new exported `PICTURE_SOURCE_MAX`, measured by the job under the plane object's 128 MB and its CPU time, admitting at least the 48 MP phone frames (8000 × 6000 and 8064 × 6048) in either orientation, in colour; a frame over it is refused `IMAGE_TOO_LARGE` before any decode, its detail naming `bound: PICTURE_SOURCE_MAX`. A PNG is judged as before: its full frame against `PICTURE_FRAME_MAX`, decoded whole by `image-codecs` R10. (Fix round 9, G124; K4835 (1)) `PICTURE_FRAME_MAX` and `PICTURE_SOURCE_MAX` stay exported, and are read from `READ_BOUNDS` (`boundOf("image", "picture_frame")`, `"picture_source"`, the alpha column holding the figures measured at T43 and T44), no numeric literal of the module's own.
- **R43** A JPEG's EXIF Orientation (APP1, tag 0x0112), values 1–8, is applied exactly, mirroring included; a missing or unreadable tag counts as 1. A PNG is never turned by its own data. (Fix round 9, G132m; K4831 (10)) A caller that has read the picture and found it turned may pass `opts.turn` (0, 90, 180 or 270 degrees clockwise): the picture, a PNG too, is turned by it after the EXIF orientation, exactly (R48).
- **R44** (T51; FR-42; K4194) A photographed page is made ready for the engine: `renderPictureToPixels(bytes, 0, {maxEdge, prepare: true})` answers R42's picture, grey (`prepare` implies `grey`), prepared as below; without `prepare` the answer is R42's, pixel-exact against Pillow, unchanged. (a) **Light and contrast:** the grain is smoothed and the light levelled, so the paper reads at least 243 across the whole picture, the mean of the brighter half of the pixels in the left, middle and right thirds of the width lying within 12 grey levels of one another, and the ink of the page reads at most 30 however little of it there is: the level is not taken from a fixed darkest fraction of the pixels, so a page of three lines of text, whose ink is under half a percent of its pixels, is levelled as a page of text and is found to hold text (d), while a blank page and noise stay as (d) says. (b) **Tilt:** the tilt of the text lines is found over ±10 degrees (`PREPARE_TILT_MAX`) and the picture is turned level by it, to within 0.5 degree of the page's true tilt, answered as `prepared.tilt_deg` (positive when the lines rise to the right); a tilt under 0.1 degree (`PREPARE_TILT_FLOOR`) is not turned, and the canvas grows to hold the turned picture whole. (c) **Scale:** a picture whose text lines are shorter than 40 px (`PREPARE_LINE_PX`, the median height of a run of rows holding ink) is enlarged, bicubic, by the factor that brings them to 40 px, at most 4 (`PREPARE_SCALE_MAX`) and never past `maxEdge`, answered as `prepared.scale`; one whose lines are 40 px or more, or whose factor is under 1.05, keeps its size (`prepared.scale` 1); a picture is never reduced here. The turn and the enlargement are one resampling. (d) **No text:** a picture with no text lines in it (a blank wall, noise: fewer than two lines, or lines over a quarter of the picture's height) is answered as R42 made it, with `prepared.text_found` false, never stretched into marks for the engine to read. The answer adds `prepared: {text_found, tilt_deg, scale, line_px}` and its `pixels_sha256` is over the prepared samples (R40: a pure function of the bytes and options). **The floor:** through `ocr-worker`'s engine (tesseract-wasm 0.11.0, `tessdata_fast`), at least 90 percent of the words of each fixture photograph (`fixtures/picture-variants.json`, `pages`: a 2.4 degree tilt, 110 dpi, uneven light with noise, and their combinations) are read from the prepared picture, where the same photographs unprepared read under 90 percent (the noisy ones 0, 26 and 23 percent). (T51 fix round 2, C18; K4316; amends R44 (c)) The preparation enlarges a page to a line height of 20 px (`PREPARE_LINE_PX`); on the hard photographed page of the tests (231 words, 110 dpi, tilt, perspective, noise, blur) the prepared reading holds at least 52 per cent of the words. (fix round 10, cause 6; K5053; amends R44 (a)) Test: a one-page picture of three lines of text (also framed 4096 x 3000 and 4097 x 3000) is answered with `prepared.text_found` true and `prepared.line_px` from 15 to 30, and `ocr-worker` reads its words; control: a blank page and noise are answered `text_found` false.
- **R45** (fix round 9, G132l; K4831 (3), K4834) **Wrong pixels are never `ok:true`.** Where a route cannot give the page's true pixels in the alpha (R22's unexamined or disagreeing JPEG pass-through, R23's `/Columns` other than `/Width`, R24's `/Decode`, `/SMask`, `/Mask` and TIFF predictor), the answer is `{ok:false, reason:"PIXELS_UNDETERMINED", why, detail}`, `detail` naming which of them (`dct_unexamined`, `ccitt_columns`, `decode_array`, `smask`, `mask`, `tiff_predictor`); the reason is a key of `REFUSALS` (R39). The decoders that would make them right are Stage 3's.
- **R46** (fix round 9, G125a; K4831 (8)) **Declared sizes are judged before any decode or allocation, in a fixed order.** For every route (R22-R25 and R42) the image dictionary's declared `/Width`, `/Height`, components and bits are judged against `boundOf("image", "pixels")` (the existing 120,000,000) and `boundOf("image", "edge")` before the stream is inflated, passed to a decoder or copied; the same check runs again for a codec's own header (`image-codecs` R12). A breach answers `IMAGE_TOO_LARGE` with the declared size and the bound in `detail`, deterministic and final, with a decode attempted at most once and nothing allocated above the stated figure (an 8 KB CCITT stream declaring 60,000 x 60,000).
- **R47** (fix round 9, G132k; F-5) **A page is rendered from the page's own bytes.** `renderPageToPixels` and `renderPictureToPixels` also accept, in place of `bytes`, a source `{size, readRange(offset, length)}`: the bytes read for one page are the cross-reference data, that page's objects and its image stream, so their total is bounded by the page and not by the file's size (a 40 MiB scanned file's page 20 reads about that page's bytes, counted through `readRange`), and the answer equals the one for the whole `bytes`. Given `bytes`, it behaves as before.
- **R48** (fix round 9, G132m; K4831 (10)) **A turned picture or page is turned upright on request.** `renderPageToPixels` and `renderPictureToPixels` accept `opts.turn` (0, 90, 180 or 270 degrees clockwise; a value that is not one of these four is ignored as 0) and apply it to the pixels after the page's `/Rotate` (R21) or the picture's EXIF orientation (R43), exactly (a bit lands on a bit for the 1-bit routes); the answer states `turned_deg` (0 when none), `upright` is `true` after it, and `pixels_sha256` is over the turned samples. The page's own `/Rotate` still always wins over `opts.rotate`, which stays ignored (R21).

## Private

### Uses

- `runtime-limits`: `READ_BOUNDS` and `boundOf(kind, name)` for every ceiling this module keeps (R42, R46, R49).
- `pdf-reader`: `openPdf`, `PdfDoc` (`pageCount`, `pageDict`, `resolve`, `dictOf`, `streamRawBytes`,
  `streamDecoded`, `isEncrypted`), `pageShowsText(doc, pageMap)`, `pdfPageImages(doc, pageIndex)` and
  `imagePlacementSource(placement)`: named services only, never a private field (N9, K28).
- `image-codecs`: the JPEG, CCITT, JBIG2 and JPX decoders and their refusal sets (R1–R4, R7); `decodePng` (R10, T43); the strip-wise JPEG decode (R11, T44).
- `setup-words`: `word`, `localize` (the words rule: a sentence people read is read by key; K3930, K3943, K3949).

### Invariants

- **R39** Every `ok:false` answer's `reason` (R42's among them, T43) is a key of the declared `REFUSALS` (pixels) or
  `CROP_REFUSALS` (crop) object, and `why` is exactly that key's own text; a reason outside the set is a
  defect in this module, never a caller's to interpret.
- **R40** Pure per call: the same bytes and options always answer the same way; no clock, no randomness,
  no state carried between requests. A decode route (R22's `decodeDct`, R23, R25) is checked pixel-exact
  against an independent decoder's reference hash, never against this module's own prior output.
- **R41** No place is named in this module's code or in any refusal text; it holds no jurisdiction data.
- **R49** (fix round 9, G124; K4835 (1)) No numeric literal in this module's code is a ceiling it keeps (R42's frame figures, R46's pixels and edge): each is read from `READ_BOUNDS`, and a test reads the module's `src` and finds none.

### Satisfies

- `BIO_Content_Framework_v0_10.md` §16, "The non-text path, in three tiers": the pixel decode tier 3
  reads through, including D-585's `pageShowsText` rule.
- `docs/development/EXTRACTION-BREADTH-DESIGN.md` §3.4 ("What a cited image resolves to") and §6: the
  crop as a derived rendition, and the pass-through/decoded-DCT routes.

### Suggestions

- `cropImage` has no production caller: only `bio-plane/test/d420-image-page.test.mjs` and
  `cpdf18-pdf-images.test.mjs` import it. `content` uses this module for it (K70).
- N34's JPX memory refusal is a `JPX_REFUSES` key in `image-codecs`; the job maps it to a `REFUSALS` reason (K70).
- The files stay in `pdf-worker/src/` (K70): a job runs this module's own tests by file, not `npm test`.

---

**Status** · In force: written by BOB #44 applying K70 (a helper module, its requirements BOB's, K20): R13–R34 and R39 moved from `pdf-worker` keeping their numbers; R41 new. Every requirement met (layer 1 closed, K284), and R44 (T51, FR-42), named by its tests.

**Status (fix round 9)** · Changed T51 fix round 9 (BOB; K4831, K4834, K4837: R20, R22-R25, R42, R43 amended; R45-R49 new; marked not yet met T51).

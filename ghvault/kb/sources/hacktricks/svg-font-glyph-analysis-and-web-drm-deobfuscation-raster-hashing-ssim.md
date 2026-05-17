---
parsed_by: focuslocust
source: hacktricks
type: generated
---
# SVG/Font Glyph Analysis & Web DRM Deobfuscation (Raster Hashing + SSIM)

[Home](../../../README.md)

## Provenance

| Field | Value |
| --- | --- |
| Source | `hacktricks` |
| Type | `hacktricks-topic` |
| Record ID | `hacktricks-generic-methodologies-and-resources-basic-forensic-methodology-specific-software-file-type-tricks-svg-font-glyph-analysis-and-web-drm-deobfuscation` |
| Source file | `/home/adams/scorchederf/focuslocust/.cache/hacktricks/src/generic-methodologies-and-resources/basic-forensic-methodology/specific-software-file-type-tricks/svg-font-glyph-analysis-and-web-drm-deobfuscation.md` |
| Parsed by | `focuslocust` |
| Relationship mode | `explicit / conservative inferred / manual` |

## Generated Concept Page

- [SVG/Font Glyph Analysis & Web DRM Deobfuscation (Raster Hashing + SSIM)](../../topics/generic-methodologies-and-resources/svg-font-glyph-analysis-and-web-drm-deobfuscation-raster-hashing-ssim.md)

## Extracted Fields

| Field | Value |
| --- | --- |
| id | hacktricks-generic-methodologies-and-resources-basic-forensic-methodology-specific-software-file-type-tricks-svg-font-glyph-analysis-and-web-drm-deobfuscation |
| name | SVG/Font Glyph Analysis & Web DRM Deobfuscation (Raster Hashing + SSIM) |
| type | hacktricks-topic |
| source | hacktricks |
| url | https://github.com/HackTricks-wiki/hacktricks/blob/master/src/generic-methodologies-and-resources/basic-forensic-methodology/specific-software-file-type-tricks/svg-font-glyph-analysis-and-web-drm-deobfuscation.md |

## Preserved Source Material

````yaml
_body: "# SVG/Font Glyph Analysis & Web DRM Deobfuscation (Raster Hashing + SSIM)\n\n{{#include ../../../banners/hacktricks-training.md}}\n\
  \nThis page documents practical techniques to recover text from web readers that ship positioned glyph runs plus per-request\
  \ vector glyph definitions (SVG paths), and that randomize glyph IDs per request to prevent scraping. The core idea is to\
  \ ignore request-scoped numeric glyph IDs and fingerprint the visual shapes via raster hashing, then map shapes to characters\
  \ with SSIM against a reference font atlas. The workflow generalizes beyond Kindle Cloud Reader to any viewer with similar\
  \ protections.\n\nWarning: Only use these techniques to back up content you legitimately own and in compliance with applicable\
  \ laws and terms.\n\n## Acquisition (example: Kindle Cloud Reader)\n\nEndpoint observed:\n- [https://read.amazon.com/renderer/render](https://read.amazon.com/renderer/render)\n\
  \nRequired materials per session:\n- Browser session cookies (normal Amazon login)\n- Rendering token from a startReading\
  \ API call\n- Additional ADP session token used by the renderer\n\nBehavior:\n- Each request, when sent with browser-equivalent\
  \ headers and cookies, returns a TAR archive limited to 5 pages.\n- For a long book you will need many batches; each batch\
  \ uses a different randomized mapping of glyph IDs.\n\nTypical TAR contents:\n- page_data_0_4.json — positioned text runs\
  \ as sequences of glyph IDs (not Unicode)\n- glyphs.json — per-request SVG path definitions for each glyph and fontFamily\n\
  - toc.json — table of contents\n- metadata.json — book metadata\n- location_map.json — logical→visual position mappings\n\
  \nExample page run structure:\n```json\n{\n  \"type\": \"TextRun\",\n  \"glyphs\": [24, 25, 74, 123, 91],\n  \"rect\": {\"\
  left\": 100, \"top\": 200, \"right\": 850, \"bottom\": 220},\n  \"fontStyle\": \"italic\",\n  \"fontWeight\": 700,\n  \"\
  fontSize\": 12.5\n}\n```\n\nExample glyphs.json entry:\n```json\n{\n  \"24\": {\"path\": \"M 450 1480 L 820 1480 L 820 0\
  \ L 1050 0 L 1050 1480 ...\", \"fontFamily\": \"bookerly_normal\"}\n}\n```\n\nNotes on anti-scraping path tricks:\n- Paths\
  \ may include micro relative moves (e.g., `m3,1 m1,6 m-4,-7`) that confuse many vector parsers and naïve path sampling.\n\
  - Always render filled complete paths with a robust SVG engine (e.g., CairoSVG) instead of doing command/coordinate differencing.\n\
  \n## Why naïve decoding fails\n\n- Per-request randomized glyph substitution: glyph ID→character mapping changes every batch;\
  \ IDs are meaningless globally.\n- Direct SVG coordinate comparison is brittle: identical shapes may differ in numeric coordinates\
  \ or command encoding per request.\n- OCR on isolated glyphs performs poorly (≈50%), confuses punctuation and look-alike\
  \ glyphs, and ignores ligatures.\n\n## Working pipeline: request-agnostic glyph normalization and mapping\n\n1) Rasterize\
  \ per-request SVG glyphs\n- Build a minimal SVG document per glyph with the provided `path` and render to a fixed canvas\
  \ (e.g., 512×512) using CairoSVG or an equivalent engine that handles tricky path sequences.\n- Render filled black on white;\
  \ avoid strokes to eliminate renderer- and AA-dependent artifacts.\n\n2) Perceptual hashing for cross-request identity\n\
  - Compute a perceptual hash (e.g., pHash via `imagehash.phash`) of each glyph image.\n- Treat the hash as a stable ID: the\
  \ same visual shape across requests collapses to the same perceptual hash, defeating randomized IDs.\n\n3) Reference font\
  \ atlas generation\n- Download the target TTF/OTF fonts (e.g., Bookerly normal/italic/bold/bold-italic).\n- Render candidates\
  \ for A–Z, a–z, 0–9, punctuation, special marks (em/en dashes, quotes), and explicit ligatures: `ff`, `fi`, `fl`, `ffi`,\
  \ `ffl`.\n- Keep separate atlases per font variant (normal/italic/bold/bold-italic).\n- Use a proper text shaper (HarfBuzz)\
  \ if you want glyph-level fidelity for ligatures; simple rasterization via Pillow ImageFont can be sufficient if you render\
  \ the ligature strings directly and the shaping engine resolves them.\n\n4) Visual similarity matching with SSIM\n- For\
  \ each unknown glyph image, compute SSIM (Structural Similarity Index) against all candidate images across all font variant\
  \ atlases.\n- Assign the character string of the best-scoring match. SSIM absorbs small antialiasing, scale, and coordinate\
  \ differences better than pixel-exact comparisons.\n\n5) Edge handling and reconstruction\n- When a glyph maps to a ligature\
  \ (multi-char), expand it during decoding.\n- Use run rectangles (top/left/right/bottom) to infer paragraph breaks (Y deltas),\
  \ alignment (X patterns), style, and sizes.\n- Serialize to HTML/EPUB preserving `fontStyle`, `fontWeight`, `fontSize`,\
  \ and internal links.\n\n### Implementation tips\n\n- Normalize all images to the same size and grayscale before hashing\
  \ and SSIM.\n- Cache by perceptual hash to avoid recomputing SSIM for repeated glyphs across batches.\n- Use a high-quality\
  \ raster size (e.g., 256–512 px) for better discrimination; downscale as needed before SSIM to accelerate.\n- If using Pillow\
  \ to render TTF candidates, set the same canvas size and center the glyph; pad to avoid clipping ascenders/descenders.\n\
  \n<details>\n<summary>Python: end-to-end glyph normalization and matching (raster hash + SSIM)</summary>\n\n```python\n\
  # pip install cairosvg pillow imagehash scikit-image uharfbuzz freetype-py\nimport io, json, tarfile, base64, math\nfrom\
  \ PIL import Image, ImageOps, ImageDraw, ImageFont\nimport imagehash\nfrom skimage.metrics import structural_similarity\
  \ as ssim\nimport cairosvg\n\nCANVAS = (512, 512)\nBGCOLOR = 255  # white\nFGCOLOR = 0    # black\n\n# --- SVG -> raster\
  \ ---\ndef rasterize_svg_path(path_d: str, canvas=CANVAS) -> Image.Image:\n    # Build a minimal SVG document; rely on CAIRO\
  \ for correct path handling\n    svg = f'''<svg xmlns=\"http://www.w3.org/2000/svg\" width=\"{canvas[0]}\" height=\"{canvas[1]}\"\
  \ viewBox=\"0 0 2048 2048\">\n<rect width=\"100%\" height=\"100%\" fill=\"white\"/>\n<path d=\"{path_d}\" fill=\"black\"\
  \ fill-rule=\"nonzero\"/>\n</svg>'''\n    png_bytes = cairosvg.svg2png(bytestring=svg.encode('utf-8'))\n    img = Image.open(io.BytesIO(png_bytes)).convert('L')\n\
  \    return img\n\n# --- Perceptual hash ---\ndef phash_img(img: Image.Image) -> str:\n    # Normalize to grayscale and\
  \ fixed size\n    img = ImageOps.grayscale(img).resize((128, 128), Image.LANCZOS)\n    return str(imagehash.phash(img))\n\
  \n# --- Reference atlas from TTF ---\ndef render_char(candidate: str, ttf_path: str, canvas=CANVAS, size=420) -> Image.Image:\n\
  \    # Render centered text on same canvas to approximate glyph shapes\n    font = ImageFont.truetype(ttf_path, size=size)\n\
  \    img = Image.new('L', canvas, color=BGCOLOR)\n    draw = ImageDraw.Draw(img)\n    w, h = draw.textbbox((0,0), candidate,\
  \ font=font)[2:]\n    dx = (canvas[0]-w)//2\n    dy = (canvas[1]-h)//2\n    draw.text((dx, dy), candidate, fill=FGCOLOR,\
  \ font=font)\n    return img\n\n# --- Build atlases for variants ---\nFONT_VARIANTS = {\n    'normal':   '/path/to/Bookerly-Regular.ttf',\n\
  \    'italic':   '/path/to/Bookerly-Italic.ttf',\n    'bold':     '/path/to/Bookerly-Bold.ttf',\n    'bolditalic':'/path/to/Bookerly-BoldItalic.ttf',\n\
  }\nCANDIDATES = [\n    *[chr(c) for c in range(0x20, 0x7F)],  # basic ASCII\n    '–', '—', '“', '”', '‘', '’', '•',    \
  \  # common punctuation\n    'ff','fi','fl','ffi','ffl'              # ligatures\n]\n\ndef build_atlases():\n    atlases\
  \ = {}  # variant -> list[(char, img)]\n    for variant, ttf in FONT_VARIANTS.items():\n        out = []\n        for ch\
  \ in CANDIDATES:\n            img = render_char(ch, ttf)\n            out.append((ch, img))\n        atlases[variant] =\
  \ out\n    return atlases\n\n# --- SSIM match ---\n\ndef best_match(img: Image.Image, atlases) -> tuple[str, float, str]:\n\
  \    # Returns (char, score, variant)\n    img_n = ImageOps.grayscale(img).resize((128,128), Image.LANCZOS)\n    img_n =\
  \ ImageOps.autocontrast(img_n)\n    best = ('', -1.0, '')\n    import numpy as np\n    candA = np.array(img_n)\n    for\
  \ variant, entries in atlases.items():\n        for ch, ref in entries:\n            ref_n = ImageOps.grayscale(ref).resize((128,128),\
  \ Image.LANCZOS)\n            ref_n = ImageOps.autocontrast(ref_n)\n            candB = np.array(ref_n)\n            score\
  \ = ssim(candA, candB)\n            if score > best[1]:\n                best = (ch, score, variant)\n    return best\n\n\
  # --- Putting it together for one TAR batch ---\n\ndef process_tar(tar_path: str, cache: dict, atlases) -> list[dict]:\n\
  \    # cache: perceptual-hash -> mapping {char, score, variant}\n    out_runs = []\n    with tarfile.open(tar_path, 'r:*')\
  \ as tf:\n        glyphs = json.load(tf.extractfile('glyphs.json'))\n        # page_data_0_4.json may differ in name; list\
  \ members to find it\n        pd_name = next(m.name for m in tf.getmembers() if m.name.startswith('page_data_'))\n     \
  \   page_data = json.load(tf.extractfile(pd_name))\n\n        # 1. Rasterize + hash all glyphs for this batch\n        id2hash\
  \ = {}\n        for gid, meta in glyphs.items():\n            img = rasterize_svg_path(meta['path'])\n            h = phash_img(img)\n\
  \            id2hash[int(gid)] = (h, img)\n\n        # 2. Ensure all hashes are resolved to characters in cache\n      \
  \  for h, img in {v[0]: v[1] for v in id2hash.values()}.items():\n            if h not in cache:\n                ch, score,\
  \ variant = best_match(img, atlases)\n                cache[h] = { 'char': ch, 'score': float(score), 'variant': variant\
  \ }\n\n        # 3. Decode text runs\n        for run in page_data:\n            if run.get('type') != 'TextRun':\n    \
  \            continue\n            decoded = []\n            for gid in run['glyphs']:\n                h, _ = id2hash[gid]\n\
  \                decoded.append(cache[h]['char'])\n            run_out = {\n                'text': ''.join(decoded),\n\
  \                'rect': run.get('rect'),\n                'fontStyle': run.get('fontStyle'),\n                'fontWeight':\
  \ run.get('fontWeight'),\n                'fontSize': run.get('fontSize'),\n            }\n            out_runs.append(run_out)\n\
  \    return out_runs\n\n# Usage sketch:\n# atlases = build_atlases()\n# cache = {}\n# for tar in sorted(glob('batches/*.tar')):\n\
  #     runs = process_tar(tar, cache, atlases)\n#     # accumulate runs for layout reconstruction → EPUB/HTML\n```\n\n</details>\n\
  \n## Layout/EPUB reconstruction heuristics\n\n- Paragraph breaks: If the next run’s top Y exceeds the previous line’s baseline\
  \ by a threshold (relative to font size), start a new paragraph.\n- Alignment: Group by similar left X for left-aligned\
  \ paragraphs; detect centered lines by symmetric margins; detect right-aligned by right edges.\n- Styling: Preserve italic/bold\
  \ via `fontStyle`/`fontWeight`; vary CSS classes by `fontSize` buckets to approximate headings vs body.\n- Links: If runs\
  \ include link metadata (e.g., `positionId`), emit anchors and internal hrefs.\n\n## Mitigating SVG anti-scraping path tricks\n\
  \n- Use filled paths with `fill-rule: nonzero` and a proper renderer (CairoSVG, resvg). Do not rely on path token normalization.\n\
  - Avoid stroke rendering; focus on filled solids to sidestep hairline artifacts caused by micro relative moves.\n- Keep\
  \ a stable viewBox per render so that identical shapes rasterize consistently across batches.\n\n## Performance notes\n\n\
  - In practice, books converge to a few hundred unique glyphs (e.g., ~361 including ligatures). Cache SSIM results by perceptual\
  \ hash.\n- After initial discovery, future batches predominantly re-use known hashes; decoding becomes I/O-bound.\n- Average\
  \ SSIM ≈0.95 is a strong signal; consider flagging low-scoring matches for manual review.\n\n## Generalization to other\
  \ viewers\n\nAny system that:\n- Returns positioned glyph runs with request-scoped numeric IDs\n- Ships per-request vector\
  \ glyphs (SVG paths or subset fonts)\n- Caps pages per request to prevent bulk export\n\n…can be handled with the same normalization:\n\
  - Rasterize per-request shapes → perceptual hash → shape ID\n- Atlas of candidate glyphs/ligatures per font variant\n- SSIM\
  \ (or similar perceptual metric) to assign characters\n- Reconstruct layout from run rectangles/styles\n\n## Minimal acquisition\
  \ example (sketch)\n\nUse your browser’s DevTools to capture the exact headers, cookies and tokens used by the reader when\
  \ requesting `/renderer/render`. Then replicate those from a script or curl. Example outline:\n\n```bash\ncurl 'https://read.amazon.com/renderer/render'\
  \ \\\n  -H 'Cookie: session-id=...; at-main=...; sess-at-main=...' \\\n  -H 'x-adp-session: <ADP_SESSION_TOKEN>' \\\n  -H\
  \ 'authorization: Bearer <RENDERING_TOKEN_FROM_startReading>' \\\n  -H 'User-Agent: <copy from browser>' \\\n  -H 'Accept:\
  \ application/x-tar' \\\n  --compressed --output batch_000.tar\n```\n\nAdjust parameterization (book ASIN, page window,\
  \ viewport) to match the reader’s requests. Expect a 5-page-per-request cap.\n\n## Results achievable\n\n- Collapse 100+\
  \ randomized alphabets to a single glyph space via perceptual hashing\n- 100% mapping of unique glyphs with average SSIM\
  \ ~0.95 when atlases include ligatures and variants\n- Reconstructed EPUB/HTML visually indistinguishable from the original\n\
  \n## References\n\n- [Kindle Web DRM: Breaking Randomized SVG Glyph Obfuscation with Raster Hashing + SSIM (Pixelmelt blog)](https://blog.pixelmelt.dev/kindle-web-drm/)\n\
  - [CairoSVG – SVG to PNG renderer](https://cairosvg.org/)\n- [imagehash – Perceptual image hashing (pHash)](https://pypi.org/project/ImageHash/)\n\
  - [scikit-image – Structural Similarity Index (SSIM)](https://scikit-image.org/docs/stable/api/skimage.metrics.html#skimage.metrics.structural_similarity)\n\
  \n{{#include ../../../banners/hacktricks-training.md}}"
_relative_path: generic-methodologies-and-resources/basic-forensic-methodology/specific-software-file-type-tricks/svg-font-glyph-analysis-and-web-drm-deobfuscation.md
_source_path: /home/adams/scorchederf/focuslocust/.cache/hacktricks/src/generic-methodologies-and-resources/basic-forensic-methodology/specific-software-file-type-tricks/svg-font-glyph-analysis-and-web-drm-deobfuscation.md
````

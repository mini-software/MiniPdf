"""
Compare MiniPdf-generated PDFs against LibreOffice reference PDFs.

Produces a detailed comparison report including:
  - Text content diff (extracted text comparison)
  - Page count comparison
  - File size comparison
  - Visual pixel diff (if pdf2image / Poppler is available)

Prerequisites:
    pip install pymupdf   # for text extraction + rendering
    pip install Pillow    # for heatmaps and composite images

Usage:
    python compare_pdfs.py [--minipdf-dir ./minipdf_pdfs] [--reference-dir ./reference_pdfs] [--report-dir ./reports]
    python compare_pdfs.py --heatmaps --heatmap-threshold 12 --heatmap-gain 5
"""

import argparse
import base64
import difflib
import json
import os
import re
import sys
from datetime import datetime
from pathlib import Path
from typing import Optional

# Try to import fitz (PyMuPDF) for text extraction and visual comparison
try:
    import fitz  # PyMuPDF
    HAS_FITZ = True
except ImportError:
    HAS_FITZ = False
    print("WARNING: PyMuPDF not installed. Install with: pip install pymupdf")
    print("         Text extraction and visual comparison will be disabled.\n")

# Try to import openai for AI-based visual comparison
try:
    import openai
    HAS_OPENAI = True
except ImportError:
    HAS_OPENAI = False


def _make_openai_client():
    """Create an OpenAI or Azure OpenAI client from environment variables.

    Supports three endpoint flavours:
      1. Azure AI Foundry / model-router  (endpoint contains /v1 path)
         → openai.OpenAI(base_url=..., api_key=...)
      2. Classic Azure OpenAI             (AZURE_OPENAI_ENDPOINT = https://resource.openai.azure.com)
         → openai.AzureOpenAI(azure_endpoint=..., api_key=...)
      3. OpenAI                           (OPENAI_API_KEY)
         → openai.OpenAI(api_key=...)

    Precedence: Azure (AZURE_OPENAI_ENDPOINT) > OpenAI (OPENAI_API_KEY).
    Returns (client, model_or_deployment) or (None, None) when no credentials found.
    """
    if not HAS_OPENAI:
        return None, None

    import re
    from urllib.parse import urlparse

    endpoint = os.environ.get("AZURE_OPENAI_ENDPOINT", "").strip().rstrip("/")
    azure_key = os.environ.get("AZURE_OPENAI_KEY", "").strip()

    if endpoint and azure_key:
        # ── AI Foundry / model-router style: endpoint contains a path (e.g. /openai/v1) ──
        parsed = urlparse(endpoint)
        if parsed.path and parsed.path not in ("", "/"):
            # Strip down to the deepest meaningful prefix (strip /chat/completions etc.)
            base = re.sub(r"/chat/completions.*$", "", endpoint)
            # Ensure it ends at /v1 or similar base path
            deployment = os.environ.get("AZURE_OPENAI_DEPLOYMENT", "gpt-4.1").strip()
            client = openai.OpenAI(api_key=azure_key, base_url=base)
            return client, deployment
        else:
            # ── Classic Azure OpenAI: only scheme+host, SDK appends /openai/deployments/... ──
            deployment = os.environ.get("AZURE_OPENAI_DEPLOYMENT", "gpt-4o").strip()
            client = openai.AzureOpenAI(
                azure_endpoint=endpoint,
                api_key=azure_key,
                api_version="2025-01-01-preview",
            )
            return client, deployment

    oai_key = os.environ.get("OPENAI_API_KEY", "").strip()
    if oai_key:
        model = os.environ.get("OPENAI_MODEL", "gpt-4o").strip()
        client = openai.OpenAI(api_key=oai_key)
        return client, model

    return None, None


AI_CLIENT, AI_MODEL = _make_openai_client()


def natural_sort_key(text: str):
    """Sort strings in human order, e.g. case2 < case10."""
    return [int(part) if part.isdigit() else part.lower() for part in re.split(r"(\d+)", text)]


def slugify_label(value: str) -> str:
    """Turn an engine/display label into a filesystem-safe lowercase token."""
    slug = re.sub(r"[^A-Za-z0-9]+", "_", value.strip().lower()).strip("_")
    return slug or "engine"


def normalize_manifest_case(entry: dict) -> dict:
    """Normalize one benchmark manifest entry into the compare_pdfs case shape."""
    if not isinstance(entry, dict):
        raise ValueError(f"Manifest case must be an object, got {type(entry).__name__}")

    case = dict(entry)
    name = (
        case.get("name")
        or case.get("pdf_stem")
        or case.get("stem")
        or case.get("case_id")
        or case.get("id")
    )
    if not name:
        raise ValueError(f"Manifest case is missing name/pdf_stem/case_id: {entry!r}")

    case["name"] = str(name)
    case.setdefault("case_id", str(name))
    return case


def load_manifest_cases(manifest_path: str) -> list[dict]:
    """Load benchmark cases from a manifest JSON file."""
    with open(manifest_path, encoding="utf-8") as f:
        data = json.load(f)

    if isinstance(data, list):
        raw_cases = data
    elif isinstance(data, dict) and isinstance(data.get("cases"), list):
        raw_cases = data["cases"]
    else:
        raise ValueError("Manifest must be a case array or an object with a 'cases' array")

    return [normalize_manifest_case(entry) for entry in raw_cases]


def case_matches_filter(case: dict, pattern: Optional[str]) -> bool:
    """Return whether a manifest case matches the existing substring filter."""
    if not pattern:
        return True

    needle = pattern.lower()
    values = [
        case.get("name"),
        case.get("case_id"),
        case.get("display_name"),
        case.get("format"),
        case.get("content_language"),
        case.get("source_path"),
    ]
    tags = case.get("tags") or []
    if isinstance(tags, str):
        values.append(tags)
    else:
        values.extend(str(tag) for tag in tags)

    return any(value is not None and needle in str(value).lower() for value in values)


def apply_case_metadata(result: dict, case_metadata: Optional[dict], report_scope: Optional[str] = None):
    """Copy stable manifest dimensions into a comparison result."""
    if report_scope:
        result["report_scope"] = report_scope
    if not case_metadata:
        return

    for key in (
        "case_id",
        "format",
        "source_path",
        "content_language",
        "display_name",
        "tags",
        "suite",
    ):
        if key in case_metadata and case_metadata[key] not in (None, ""):
            result[key] = case_metadata[key]


def result_display_name(result: dict) -> str:
    return str(result.get("display_name") or result.get("name") or "")


def result_metadata_summary(result: dict) -> str:
    parts = []
    for label, key in (
        ("format", "format"),
        ("case", "case_id"),
        ("language", "content_language"),
        ("scope", "report_scope"),
    ):
        value = result.get(key)
        if value:
            parts.append(f"{label}: {value}")
    return " | ".join(parts)


def save_composite_image(components: list[tuple[str, str]], output_path: str) -> bool:
    """Create one labeled side-by-side image from already-rendered page PNGs."""
    try:
        from PIL import Image, ImageDraw, ImageFont
    except ImportError:
        return False

    opened = []
    for label, path in components:
        if path and os.path.isfile(path):
            opened.append((label, Image.open(path).convert("RGB")))
    if len(opened) < 2:
        return False

    target_height = min(image.height for _, image in opened)
    resized = []
    for label, image in opened:
        if image.height != target_height:
            width = round(image.width * target_height / image.height)
            image = image.resize((width, target_height), Image.LANCZOS)
        resized.append((label, image))

    pad = 24
    label_height = 36
    total_width = sum(image.width for _, image in resized) + pad * (len(resized) + 1)
    total_height = target_height + label_height + pad * 2
    canvas = Image.new("RGB", (total_width, total_height), "white")
    draw = ImageDraw.Draw(canvas)
    font = ImageFont.load_default()

    x = pad
    for label, image in resized:
        draw.text((x, pad // 2), label, fill=(20, 20, 20), font=font)
        canvas.paste(image, (x, label_height + pad))
        x += image.width + pad

    canvas.save(output_path)
    return True

_AI_SYSTEM_PROMPT = """\
You are an expert PDF rendering quality analyst.
You will be given two images of the same spreadsheet page:
  Image 1 (left/first): rendered by MiniPdf (the candidate)
  Image 2 (right/second): rendered by LibreOffice (the gold reference)

Analyse the visual differences and return a JSON object with exactly these fields:
{
  "differences": [   // list of specific observed differences (strings)
  ],
  "severity": "low|medium|high",  // overall severity
  "ai_visual_score": 0.0,          // float 0.0-1.0 (1.0 = visually identical)
  "suggestions": [   // actionable code improvement suggestions (strings)
  ]
}

Focus on:
- Cell border rendering (missing, extra, wrong weight/color)
- Column widths and row heights
- Font family, size, and weight
- Text truncation or overflow
- Background / fill colors
- Number/date formatting
- Header row styling
- Page margins and overall layout

Return ONLY valid JSON. No markdown fences, no extra text.
"""


def ai_compare_pages(img_minipdf: str, img_reference: str) -> dict:
    """Send two page images to the vision model and return structured AI analysis.

    Returns a dict with keys: differences, severity, ai_visual_score, suggestions.
    On error returns a dict with an 'error' key.
    """
    if AI_CLIENT is None:
        return {"error": "No OpenAI credentials configured"}

    def _encode(path: str) -> str:
        with open(path, "rb") as f:
            return base64.b64encode(f.read()).decode()

    try:
        b64_mini = _encode(img_minipdf)
        b64_ref = _encode(img_reference)
    except OSError as e:
        return {"error": f"Cannot read image: {e}"}

    messages = [
        {"role": "system", "content": _AI_SYSTEM_PROMPT},
        {
            "role": "user",
            "content": [
                {"type": "text", "text": "Compare these two PDF page renderings and return JSON analysis."},
                {"type": "image_url", "image_url": {"url": f"data:image/png;base64,{b64_mini}", "detail": "high"}},
                {"type": "image_url", "image_url": {"url": f"data:image/png;base64,{b64_ref}", "detail": "high"}},
            ],
        },
    ]

    try:
        response = AI_CLIENT.chat.completions.create(
            model=AI_MODEL,
            messages=messages,
            max_tokens=1024,
            temperature=0,
        )
        raw = response.choices[0].message.content.strip()
        # Strip optional markdown fences
        if raw.startswith("```"):
            raw = raw.split("\n", 1)[-1].rsplit("```", 1)[0].strip()
        return json.loads(raw)
    except json.JSONDecodeError as e:
        return {"error": f"AI returned non-JSON: {e}", "raw": raw}
    except Exception as e:
        return {"error": str(e)}


def extract_text_pymupdf(pdf_path: str) -> list[str]:
    """Extract text from each page using PyMuPDF.
    Groups spans at the same Y position (same visual row) into a single
    space-joined line so that MiniPdf and LibreOffice outputs are comparable
    regardless of whether each cell is a separate span or part of a row span."""
    pages = []
    doc = fitz.open(pdf_path)
    for page in doc:
        data = page.get_text("dict", sort=True)
        spans = []
        for block in data.get("blocks", []):
            if block.get("type", 0) != 0:
                continue
            for line in block.get("lines", []):
                for span in line.get("spans", []):
                    text = span.get("text", "").strip()
                    if text:
                        # Use the text origin (baseline) Y instead of bbox top Y.
                        # Different fonts (e.g. CJK vs Latin) report different
                        # ascent metrics, making bbox Y inconsistent even when
                        # the actual baseline is identical.
                        y_key = span.get("origin", (span["bbox"][0], span["bbox"][1]))[1]
                        spans.append((round(y_key, 1), span["bbox"][0], text))
        # Sort by Y then X position
        spans.sort()
        # Group spans that share the same Y row (within 1.0 pt tolerance) into
        # a single whitespace-separated line — this handles the structural
        # difference between PDF renderers that emit one span per cell vs
        # one span per row.
        # Within each group we sort by X so that left-to-right column order is
        # preserved even when spans from different renderers land at slightly
        # different sub-pixel Y positions (< 1 pt apart).
        lines = []
        current_y = None
        current_tokens: list[tuple[float, str]] = []  # (x, text)
        for y, x, text in spans:
            if current_y is None or abs(y - current_y) > 1.0:
                if current_tokens:
                    current_tokens.sort()
                    lines.append(" ".join(t for _, t in current_tokens))
                current_y = y
                current_tokens = [(x, text)]
            else:
                current_tokens.append((x, text))
        if current_tokens:
            current_tokens.sort()
            lines.append(" ".join(t for _, t in current_tokens))
        pages.append("\n".join(lines))
    doc.close()
    return pages


def extract_text_fallback(pdf_path: str) -> list[str]:
    """Fallback: extract raw ASCII strings from PDF binary."""
    with open(pdf_path, "rb") as f:
        data = f.read()
    # Very rough extraction: find text between BT..ET operators
    text = data.decode("latin-1", errors="replace")
    # Extract parenthesized strings (PDF text objects)
    import re
    strings = re.findall(r"\(([^)]*)\)", text)
    return ["\n".join(strings)]


def render_page_to_pixels(pdf_path: str, page_num: int, dpi: int = 150):
    """Render a PDF page to a pixel map using PyMuPDF. Returns (width, height, samples)."""
    doc = fitz.open(pdf_path)
    if page_num >= len(doc):
        doc.close()
        return None
    page = doc[page_num]
    mat = fitz.Matrix(dpi / 72, dpi / 72)
    pix = page.get_pixmap(matrix=mat, alpha=False)
    result = (pix.width, pix.height, pix.samples)
    doc.close()
    return result


def _aligned_rgb_images(pix1, pix2):
    """Convert two pixel tuples to equally sized RGB PIL images."""
    if pix1 is None or pix2 is None:
        return None, None

    from PIL import Image

    def to_image(pix):
        width, height, samples = pix
        channels = len(samples) // (width * height)
        mode = "RGB" if channels == 3 else "RGBA"
        return Image.frombytes(mode, (width, height), bytes(samples)).convert("RGB")

    image1 = to_image(pix1)
    image2 = to_image(pix2)
    if image1.size != image2.size:
        target_size = (min(image1.width, image2.width), min(image1.height, image2.height))
        image1 = image1.resize(target_size, Image.LANCZOS)
        image2 = image2.resize(target_size, Image.LANCZOS)
    return image1, image2


def _save_normalized_pixmaps(pixmaps, paths, aspect_tolerance: float = 0.001):
    """Save same-aspect page pixmaps at a common size without hiding paper-size differences."""
    available = [(pix, path) for pix, path in zip(pixmaps, paths) if pix and path]
    if not available:
        return

    aspect_ratios = [pix.width / pix.height for pix, _ in available]
    same_aspect = max(aspect_ratios) - min(aspect_ratios) <= aspect_tolerance
    if not same_aspect:
        for pix, path in available:
            pix.save(path)
        return

    from PIL import Image

    target_size = (
        min(pix.width for pix, _ in available),
        min(pix.height for pix, _ in available),
    )
    for pix, path in available:
        if (pix.width, pix.height) == target_size:
            pix.save(path)
            continue

        channels = pix.n
        mode = "RGB" if channels == 3 else "RGBA"
        image = Image.frombytes(mode, (pix.width, pix.height), pix.samples).convert("RGB")
        image.resize(target_size, Image.LANCZOS).save(path)


def save_difference_heatmap(
    pix1,
    pix2,
    output_path: str,
    threshold: int = 12,
    gain: float = 5.0,
) -> Optional[dict]:
    """Write a contextual blue-to-red difference heatmap and return metrics."""
    try:
        from PIL import Image, ImageChops, ImageOps, ImageStat
    except ImportError:
        return None

    image1, image2 = _aligned_rgb_images(pix1, pix2)
    if image1 is None or image2 is None:
        return None

    threshold = max(0, min(255, int(threshold)))
    gain = max(0.1, float(gain))
    difference = ImageChops.difference(image1, image2)
    red, green, blue = difference.split()
    intensity = ImageChops.lighter(ImageChops.lighter(red, green), blue)
    changed_mask = intensity.point(lambda value: 255 if value > threshold else 0)
    difference_bbox = changed_mask.getbbox()

    signal_lut = [
        0 if value <= threshold else min(255, round((value - threshold) * gain))
        for value in range(256)
    ]
    signal = intensity.point(signal_lut)
    heat = ImageOps.colorize(signal, black=(45, 55, 225), white=(255, 45, 35))
    context = ImageOps.grayscale(image2).convert("RGB")
    contextual_heat = Image.blend(context, heat, 0.80)
    contextual_heat.save(output_path)

    histogram = changed_mask.histogram()
    changed_pixels = sum(histogram[1:])
    total_pixels = image1.width * image1.height
    stats = ImageStat.Stat(difference)
    rmse = (sum(channel_rms ** 2 for channel_rms in stats.rms) / len(stats.rms)) ** 0.5
    return {
        "size_px": [image1.width, image1.height],
        "difference_bbox_px": list(difference_bbox) if difference_bbox else None,
        "changed_pixels": changed_pixels,
        "changed_fraction": round(changed_pixels / total_pixels, 6) if total_pixels else 0.0,
        "mean_abs_rgb": round(sum(stats.mean) / len(stats.mean), 4),
        "rmse_rgb": round(rmse, 4),
        "threshold": threshold,
        "gain": gain,
    }


def pixel_diff_score(pix1, pix2, grid_n: int = 20) -> float:
    """
    Compare two pixmaps and return a structural similarity score 0.0-1.0.
    1.0 = identical, 0.0 = completely different.

    Uses three components:
      1. Raw byte-match score with a content-coverage penalty.
      2. Grid content-density score: divide the page into grid_n×grid_n cells
         and compare the *fraction of non-white pixels* in each cell.
         This is sensitive to layout differences (e.g. a header row present in
         one rendering but missing in the other, or content compressed into a
         different region) that raw byte-matching misses because white background
         dominates the byte count.
      3. Top-strip score: compare the top 15% of the page separately with high
         weight to catch missing header rows.

    Final score = 0.40 * raw + 0.40 * grid_density + 0.20 * top_strip
    """
    if pix1 is None or pix2 is None:
        return 0.0

    w1, h1, s1 = pix1
    w2, h2, s2 = pix2

    if w1 != w2 or h1 != h2:
        # Resize both images to the smaller dimensions so the full comparison
        # algorithm can run instead of the old byte-level fallback.
        try:
            from PIL import Image
            ch1 = len(s1) // (w1 * h1)
            ch2 = len(s2) // (w2 * h2)
            mode1 = "RGB" if ch1 == 3 else "RGBA"
            mode2 = "RGB" if ch2 == 3 else "RGBA"
            img1 = Image.frombytes(mode1, (w1, h1), bytes(s1))
            img2 = Image.frombytes(mode2, (w2, h2), bytes(s2))
            tw, th = min(w1, w2), min(h1, h2)
            img1 = img1.resize((tw, th), Image.LANCZOS).convert("RGB")
            img2 = img2.resize((tw, th), Image.LANCZOS).convert("RGB")
            s1 = img1.tobytes()
            s2 = img2.tobytes()
            w1 = h1 = None  # trigger re-assignment below
            w1, h1 = tw, th
            w2, h2 = tw, th
        except Exception:
            min_len = min(len(s1), len(s2))
            if min_len == 0:
                return 0.0
            matching = sum(1 for a, b in zip(s1[:min_len], s2[:min_len]) if a == b)
            return matching / min_len

    total = len(s1)
    if total == 0:
        return 1.0

    channels = len(s1) // (w1 * h1)  # 3 for RGB

    # ── Raw byte score ────────────────────────────────────────────────────────
    matching = 0
    nonwhite_mini = 0
    nonwhite_ref = 0
    for a, b in zip(s1, s2):
        if a == b:
            matching += 1
        if a != 255:
            nonwhite_mini += 1
        if b != 255:
            nonwhite_ref += 1

    raw_score = matching / total
    if nonwhite_ref > total * 0.005:
        coverage = nonwhite_mini / nonwhite_ref
        if coverage < 0.5:
            raw_score *= min(1.0, coverage * 2)

    # ── Helper: non-white pixel density in a rectangular region ──────────────
    def region_density(samples, y0, y1, x0, x1):
        nw = tot = 0
        for cy in range(y0, y1):
            row_off = cy * w1 * channels
            for cx in range(x0, x1):
                off = row_off + cx * channels
                r, g, b = samples[off], samples[off+1], samples[off+2]
                if r != 255 or g != 255 or b != 255:
                    nw += 1
                tot += 1
        return nw / tot if tot else 0.0

    # ── Grid content-density score ────────────────────────────────────────────
    cell_w = max(1, w1 // grid_n)
    cell_h = max(1, h1 // grid_n)
    density_diffs = []
    for gy in range(grid_n):
        y0 = gy * cell_h
        y1 = y0 + cell_h if gy < grid_n - 1 else h1
        for gx in range(grid_n):
            x0 = gx * cell_w
            x1 = x0 + cell_w if gx < grid_n - 1 else w1
            d1 = region_density(s1, y0, y1, x0, x1)
            d2 = region_density(s2, y0, y1, x0, x1)
            # Amplify differences in cells that have content in the reference
            weight = 1.0 + d2 * 4  # content cells count up to 5× more
            density_diffs.append((abs(d1 - d2), weight))

    total_w = sum(w for _, w in density_diffs)
    grid_score = 1.0 - sum(d * w for d, w in density_diffs) / total_w if total_w else 1.0
    grid_score = max(0.0, grid_score)

    # ── Top-strip score (top 15% of page = header area) ──────────────────────
    top_h = max(1, int(h1 * 0.15))
    d1_top = region_density(s1, 0, top_h, 0, w1)
    d2_top = region_density(s2, 0, top_h, 0, w1)
    # If reference has a header (non-white) but MiniPdf doesn't → penalise
    top_score = 1.0 - abs(d1_top - d2_top) * 3  # amplified penalty
    top_score = max(0.0, min(1.0, top_score))

    return round(0.40 * raw_score + 0.40 * grid_score + 0.20 * top_score, 4)


def save_visual_diff(
    pdf1_path: str,
    pdf2_path: str,
    output_dir: str,
    name: str,
    dpi: int = 150,
    auxiliary_pdf_path=None,
    composite_output_dir: Optional[str] = None,
    labels: Optional[dict] = None,
    heatmaps: bool = False,
    heatmap_threshold: int = 12,
    heatmap_gain: float = 5.0,
    max_compare_pages: int = 0,
):
    """Save visual diff images for each page."""
    if not HAS_FITZ:
        return []

    labels = labels or {}
    candidate_label = labels.get("candidate", "MiniPdf")
    reference_label = labels.get("reference", "LibreOffice Reference")
    auxiliary_label = labels.get("auxiliary", "Auxiliary Reference")
    auxiliary_slug = slugify_label(auxiliary_label)

    # Remove stale images from previous runs with different page counts
    import glob
    for suffix in ("minipdf", "reference", "office", "libreoffice_auxiliary_reference", auxiliary_slug, "heatmap"):
        if max_compare_pages > 0:
            old_images = (
                os.path.join(output_dir, f"{name}_p{page}_{suffix}.png")
                for page in range(1, max_compare_pages + 1)
            )
        else:
            old_images = glob.glob(os.path.join(output_dir, f"{glob.escape(name)}_p*_{suffix}.png"))
        for old in old_images:
            if not os.path.isfile(old):
                continue
            os.remove(old)
    if composite_output_dir:
        os.makedirs(composite_output_dir, exist_ok=True)
        for old in glob.glob(os.path.join(composite_output_dir, f"{glob.escape(name)}_p*_*.png")):
            os.remove(old)

    diff_images = []
    doc1 = fitz.open(pdf1_path)
    doc2 = fitz.open(pdf2_path)
    doc3 = fitz.open(auxiliary_pdf_path) if auxiliary_pdf_path and os.path.isfile(auxiliary_pdf_path) else None
    max_pages = max(len(doc1), len(doc2), len(doc3) if doc3 else 0)
    if max_compare_pages > 0:
        max_pages = min(max_pages, max_compare_pages)

    for i in range(max_pages):
        mat = fitz.Matrix(dpi / 72, dpi / 72)

        if i < len(doc1):
            pix1 = doc1[i].get_pixmap(matrix=mat, alpha=False)
        else:
            pix1 = None

        if i < len(doc2):
            pix2 = doc2[i].get_pixmap(matrix=mat, alpha=False)
        else:
            pix2 = None

        pix3 = None
        if doc3 and i < len(doc3):
            pix3 = doc3[i].get_pixmap(matrix=mat, alpha=False)

        # Save individual renderings
        path1 = None
        path2 = None
        path3 = None

        if pix1:
            path1 = os.path.join(output_dir, f"{name}_p{i+1}_minipdf.png")

        if pix2:
            path2 = os.path.join(output_dir, f"{name}_p{i+1}_reference.png")

        if pix3:
            path3 = os.path.join(output_dir, f"{name}_p{i+1}_{auxiliary_slug}.png")

        _save_normalized_pixmaps(
            (pix1, pix2, pix3),
            (path1, path2, path3),
        )

        entry = {
            "page": i + 1,
            "minipdf_img": f"{name}_p{i+1}_minipdf.png" if pix1 else None,
            "reference_img": f"{name}_p{i+1}_reference.png" if pix2 else None,
        }
        if doc3 is not None:
            entry["auxiliary_img"] = f"{name}_p{i+1}_{auxiliary_slug}.png" if pix3 else None
        if heatmaps and pix1 and pix2:
            heatmap_name = f"{name}_p{i+1}_heatmap.png"
            heatmap_path = os.path.join(output_dir, heatmap_name)
            heatmap_metrics = save_difference_heatmap(
                (pix1.width, pix1.height, pix1.samples),
                (pix2.width, pix2.height, pix2.samples),
                heatmap_path,
                threshold=heatmap_threshold,
                gain=heatmap_gain,
            )
            if heatmap_metrics:
                entry["heatmap_img"] = heatmap_name
                entry["heatmap_metrics"] = heatmap_metrics
        if composite_output_dir:
            engine_slugs = [slugify_label(candidate_label), slugify_label(reference_label)]
            components = [(candidate_label, path1), (reference_label, path2)]
            if doc3 is not None:
                engine_slugs.append(auxiliary_slug)
                components.append((auxiliary_label, path3))

            composite_name = f"{name}_p{i+1}_{'_vs_'.join(engine_slugs)}.png"
            composite_path = os.path.join(composite_output_dir, composite_name)
            if save_composite_image(components, composite_path):
                entry["composite_img"] = composite_name
        diff_images.append(entry)

    doc1.close()
    doc2.close()
    if doc3:
        doc3.close()
    return diff_images


def validate_pdf_structure(pdf_path: str) -> dict:
    """Validate PDF internal structure: xref offsets, stream lengths, header/trailer.

    Returns a dict with:
      - valid (bool): True if no structural errors found
      - errors (list[str]): descriptions of any issues detected
    """
    errors = []
    try:
        with open(pdf_path, "rb") as f:
            raw = f.read()
    except Exception as e:
        return {"valid": False, "errors": [f"Cannot read file: {e}"]}

    text = raw.decode("latin-1")

    # 1. Header check
    if not text.startswith("%PDF-"):
        errors.append("Missing %PDF- header")

    # 2. EOF check
    if "%%EOF" not in text[-64:]:
        errors.append("Missing %%EOF at end of file")

    # 3. Find xref table via startxref pointer
    m_startxref = re.search(r"startxref\s+(\d+)\s+%%EOF", text)
    if not m_startxref:
        errors.append("Cannot locate startxref pointer")
        return {"valid": len(errors) == 0, "errors": errors}

    xref_offset = int(m_startxref.group(1))
    if not text[xref_offset:].startswith("xref\n"):
        errors.append(f"startxref offset {xref_offset} does not point to 'xref' keyword")
        return {"valid": False, "errors": errors}

    # 4. Parse xref entries and validate offsets
    xref_section = text[xref_offset:]
    trailer_pos = xref_section.find("trailer")
    if trailer_pos < 0:
        errors.append("No trailer found after xref")
        return {"valid": False, "errors": errors}

    xref_body = xref_section[:trailer_pos].strip()
    xref_lines = xref_body.split("\n")
    if len(xref_lines) < 2:
        errors.append("xref table too short")
        return {"valid": False, "errors": errors}

    parts = xref_lines[1].split()
    start_obj = int(parts[0])
    num_objs = int(parts[1])

    for idx in range(2, min(2 + num_objs, len(xref_lines))):
        entry = xref_lines[idx]
        if "f" in entry:
            continue
        offset = int(entry[:10])
        obj_num = start_obj + idx - 2
        # Verify the bytes at this offset start with "N 0 obj"
        actual = raw[offset : offset + len(str(obj_num)) + 6].decode("latin-1", errors="replace")
        expected = f"{obj_num} 0 obj"
        if not actual.startswith(expected):
            errors.append(f"xref obj {obj_num}: offset {offset} -> found {actual!r}, expected {expected!r}")

    # 5. Validate stream lengths
    for m in re.finditer(r"/Length (\d+)\s*>>(?:\n|\r\n?)stream(?:\n|\r\n?)", text):
        declared = int(m.group(1))
        stream_start = m.end()
        endstream_pos = raw.find(b"\nendstream", stream_start)
        if endstream_pos < 0:
            endstream_pos = raw.find(b"\r\nendstream", stream_start)
        if endstream_pos < 0:
            errors.append(f"Missing endstream for stream at offset {stream_start}")
            continue
        actual_len = endstream_pos - stream_start
        if declared != actual_len:
            errors.append(f"Stream at {stream_start}: declared length {declared}, actual {actual_len}")

    return {"valid": len(errors) == 0, "errors": errors}


def compare_single(
    minipdf_path: str,
    reference_path: str,
    report_images_dir: str,
    name: str,
    ai_compare: bool = False,
    ai_max_pages: int = 1,
    ai_threshold: float = 1.01,
    auxiliary_path=None,
    case_metadata: Optional[dict] = None,
    report_scope: Optional[str] = None,
    composite_images: bool = False,
    composite_output_dir: Optional[str] = None,
    labels: Optional[dict] = None,
    heatmaps: bool = False,
    heatmap_threshold: int = 12,
    heatmap_gain: float = 5.0,
    max_compare_pages: int = 0,
) -> dict:
    """Compare a single pair of PDFs and return a detailed result."""
    result = {
        "name": name,
        "minipdf_exists": os.path.isfile(minipdf_path),
        "reference_exists": os.path.isfile(reference_path),
    }
    apply_case_metadata(result, case_metadata, report_scope)

    if not result["minipdf_exists"]:
        result["error"] = "MiniPdf PDF not found"
        result["score"] = 0.0
        return result

    if not result["reference_exists"]:
        result["error"] = "Reference PDF not found"
        result["score"] = 0.0
        return result

    # File sizes
    result["minipdf_size"] = os.path.getsize(minipdf_path)
    result["reference_size"] = os.path.getsize(reference_path)

    # PDF structure validation (xref offsets, stream lengths)
    validity = validate_pdf_structure(minipdf_path)
    result["pdf_valid"] = validity["valid"]
    if not validity["valid"]:
        result["pdf_errors"] = validity["errors"]
        print(f"  ⚠ PDF structure errors in {name}: {validity['errors'][:3]}")

    # Page counts
    if HAS_FITZ:
        doc_m = fitz.open(minipdf_path)
        doc_r = fitz.open(reference_path)
        result["minipdf_pages"] = len(doc_m)
        result["reference_pages"] = len(doc_r)
        doc_m.close()
        doc_r.close()
    else:
        result["minipdf_pages"] = "?"
        result["reference_pages"] = "?"

    # Text extraction and comparison
    if HAS_FITZ:
        try:
            text_m = extract_text_pymupdf(minipdf_path)
            text_r = extract_text_pymupdf(reference_path)
        except Exception as e:
            text_m = extract_text_fallback(minipdf_path)
            text_r = extract_text_fallback(reference_path)
            result["text_extract_warning"] = str(e)
    else:
        text_m = extract_text_fallback(minipdf_path)
        text_r = extract_text_fallback(reference_path)

    if max_compare_pages > 0:
        text_m = text_m[:max_compare_pages]
        text_r = text_r[:max_compare_pages]
        result["compared_pages"] = max_compare_pages

    # Flatten text for comparison
    flat_m = "\n---PAGE---\n".join(text_m).strip()
    flat_r = "\n---PAGE---\n".join(text_r).strip()

    # Text similarity (SequenceMatcher) — page-aware
    if len(flat_m) == 0 and len(flat_r) == 0:
        # Both empty — treat as identical
        result["text_similarity"] = 1.0
    else:
        sm = difflib.SequenceMatcher(None, flat_m, flat_r)
        result["text_similarity"] = round(sm.ratio(), 4)

    # Also compute flat text similarity (ignoring page breaks)
    # This is fairer when page break positions differ but content is the same
    flat_m_no_page = flat_m.replace("\n---PAGE---\n", "\n")
    flat_r_no_page = flat_r.replace("\n---PAGE---\n", "\n")
    if len(flat_m_no_page) == 0 and len(flat_r_no_page) == 0:
        result["flat_text_similarity"] = 1.0
    else:
        sm_flat = difflib.SequenceMatcher(None, flat_m_no_page, flat_r_no_page)
        result["flat_text_similarity"] = round(sm_flat.ratio(), 4)

    # Word-level similarity: compare word-token sequences — far more robust than
    # character-level matching when the only differences are truncation or minor
    # word-boundary shifts (e.g. "Grilled Salmon" vs "Grilled S")
    words_m = flat_m_no_page.split()
    words_r = flat_r_no_page.split()
    if len(words_m) == 0 and len(words_r) == 0:
        result["word_text_similarity"] = 1.0
    else:
        sm_words = difflib.SequenceMatcher(None, words_m, words_r)
        result["word_text_similarity"] = round(sm_words.ratio(), 4)

    # Use the highest of all similarity metrics
    result["text_similarity"] = max(
        result["text_similarity"],
        result["flat_text_similarity"],
        result["word_text_similarity"],
    )

    # Unified diff
    diff_lines = list(difflib.unified_diff(
        flat_m.splitlines(keepends=True),
        flat_r.splitlines(keepends=True),
        fromfile=f"minipdf/{name}.pdf",
        tofile=f"reference/{name}.pdf",
        lineterm="",
    ))
    result["text_diff"] = "\n".join(diff_lines) if diff_lines else "(identical)"

    # Visual comparison
    visual_scores = []
    if HAS_FITZ:
        max_pages = max(result["minipdf_pages"], result["reference_pages"])
        if max_compare_pages > 0:
            max_pages = min(max_pages, max_compare_pages)
        for p in range(max_pages):
            pix_m = render_page_to_pixels(minipdf_path, p)
            pix_r = render_page_to_pixels(reference_path, p)
            score = pixel_diff_score(pix_m, pix_r)
            visual_scores.append(round(score, 4))

        result["visual_scores"] = visual_scores
        result["visual_avg"] = round(sum(visual_scores) / len(visual_scores), 4) if visual_scores else 0.0

        # Save diff images
        os.makedirs(report_images_dir, exist_ok=True)
        result["diff_images"] = save_visual_diff(
            minipdf_path,
            reference_path,
            report_images_dir,
            name,
            auxiliary_pdf_path=auxiliary_path,
            composite_output_dir=composite_output_dir if composite_images else None,
            labels=labels,
            heatmaps=heatmaps,
            heatmap_threshold=heatmap_threshold,
            heatmap_gain=heatmap_gain,
            max_compare_pages=max_compare_pages,
        )

        # ── AI visual comparison ──────────────────────────────────────────────
        if ai_compare and AI_CLIENT is not None:
            ai_results = []
            pages_to_analyse = min(ai_max_pages, max(result["minipdf_pages"], result["reference_pages"]))
            for p_idx in range(pages_to_analyse):
                pix_score = visual_scores[p_idx] if p_idx < len(visual_scores) else 1.0
                if pix_score >= ai_threshold:
                    # Pixel score is already good — skip AI call to save cost
                    ai_results.append({"page": p_idx + 1, "skipped": True, "reason": "pixel_score_above_threshold"})
                    continue
                img_mini = os.path.join(report_images_dir, f"{name}_p{p_idx+1}_minipdf.png")
                img_ref = os.path.join(report_images_dir, f"{name}_p{p_idx+1}_reference.png")
                if not os.path.isfile(img_mini) or not os.path.isfile(img_ref):
                    ai_results.append({"page": p_idx + 1, "error": "image not found"})
                    continue
                print(f"    [AI] analysing page {p_idx + 1} of {name} ...", end=" ", flush=True)
                analysis = ai_compare_pages(img_mini, img_ref)
                analysis["page"] = p_idx + 1
                ai_results.append(analysis)
                if "error" not in analysis:
                    print(f"severity={analysis.get('severity','?')} score={analysis.get('ai_visual_score','?')}")
                else:
                    print(f"error: {analysis['error']}")
            result["ai_analysis"] = ai_results

            # Override visual avg with AI score when available
            ai_scores = [
                a.get("ai_visual_score")
                for a in ai_results
                if isinstance(a.get("ai_visual_score"), (int, float))
            ]
            if ai_scores:
                result["ai_visual_avg"] = round(sum(ai_scores) / len(ai_scores), 4)
        elif ai_compare and AI_CLIENT is None:
            result["ai_analysis_warning"] = (
                "AI comparison requested but no credentials found. "
                "Set OPENAI_API_KEY or AZURE_OPENAI_ENDPOINT + AZURE_OPENAI_KEY."
            )

    # Overall score: weighted average
    # When AI scores are available they replace the noisy pixel score for visual dimension
    page_score = 1.0 if result.get("minipdf_pages") == result.get("reference_pages") else 0.5
    text_score = result["text_similarity"]
    vis_score = result.get("ai_visual_avg",          # prefer AI score
                 result.get("visual_avg",             # fall back to pixel
                            text_score))               # last resort: text

    result["overall_score"] = round(text_score * 0.4 + vis_score * 0.4 + page_score * 0.2, 4)

    return result


def generate_report(results: list[dict], report_dir: str, labels: dict | None = None):
    """Generate a markdown + JSON comparison report."""
    labels = labels or {}
    candidate_label = labels.get("candidate", "MiniPdf")
    reference_label = labels.get("reference", "Reference")
    auxiliary_label = labels.get("auxiliary", "Auxiliary Reference")
    # JSON dump
    json_path = os.path.join(report_dir, "comparison_report.json")
    with open(json_path, "w", encoding="utf-8") as f:
        json.dump(results, f, indent=2, ensure_ascii=False, default=str)

    # Markdown report
    md_path = os.path.join(report_dir, "comparison_report.md")
    with open(md_path, "w", encoding="utf-8") as f:
        f.write(f"# {candidate_label} vs {reference_label} PDF Comparison Report\n\n")
        f.write(f"Generated: {datetime.now().isoformat()}\n\n")

        # Summary table
        f.write("## Summary\n\n")
        f.write("| # | Test Case | Valid | Text Sim | Visual Avg | Pages (M/R) | Overall |\n")
        f.write("|---|-----------|-------|----------|------------|-------------|--------|\n")

        for i, r in enumerate(results, 1):
            name = r["name"]
            pdf_valid = "✅" if r.get("pdf_valid", True) else "❌"
            text_sim = r.get("text_similarity", "N/A")
            vis_avg = r.get("visual_avg", "N/A")
            mp = r.get("minipdf_pages", "?")
            rp = r.get("reference_pages", "?")
            overall = r.get("overall_score", "N/A")

            # Color coding via emoji
            if isinstance(overall, (int, float)):
                if overall >= 0.9:
                    emoji = "🟢"
                elif overall >= 0.7:
                    emoji = "🟡"
                else:
                    emoji = "🔴"
            else:
                emoji = "⚪"

            f.write(f"| {i} | {emoji} {name} | {pdf_valid} | {text_sim} | {vis_avg} | {mp}/{rp} | **{overall}** |\n")

        avg_overall = sum(r.get("overall_score", 0) for r in results) / len(results) if results else 0
        f.write(f"\n**Average Overall Score: {avg_overall:.4f}**\n\n")

        has_composite = any(
            pg.get("composite_img")
            for r in results
            for pg in r.get("diff_images", [])
        )
        if has_composite:
            f.write("## Labeled Side-by-Side Comparison\n\n")
            f.write("<table>\n")
            f.write("<tr><th>Case</th><th>Comparison</th></tr>\n")
            for r in results:
                display_name = result_display_name(r)
                metadata = result_metadata_summary(r)
                title = display_name if not metadata else f"{display_name}<br><small>{metadata}</small>"
                for idx, pg in enumerate(r.get("diff_images", [])):
                    composite_img = pg.get("composite_img")
                    if not composite_img:
                        continue
                    page_num = pg.get("page", idx + 1)
                    f.write("<tr>\n")
                    f.write(f"  <td><b>{title}</b><br>Page {page_num}</td>\n")
                    f.write(
                        f"  <td><img src=\"side-by-side/{composite_img}\" "
                        f"width=\"760\" alt=\"{display_name} page {page_num} comparison\"></td>\n"
                    )
                    f.write("</tr>\n")
            f.write("</table>\n\n")

        has_heatmaps = any(
            pg.get("heatmap_img")
            for r in results
            for pg in r.get("diff_images", [])
        )
        if has_heatmaps:
            f.write("## Difference Heatmaps\n\n")
            f.write("Blue areas are below the configured difference threshold; red areas have stronger pixel differences. The reference rendering is retained as faint context.\n\n")
            f.write("<table>\n")
            f.write("<tr><th>Case</th><th>Heatmap</th><th>Metrics</th></tr>\n")
            for r in results:
                display_name = result_display_name(r)
                for idx, pg in enumerate(r.get("diff_images", [])):
                    heatmap_img = pg.get("heatmap_img")
                    if not heatmap_img:
                        continue
                    page_num = pg.get("page", idx + 1)
                    metrics = pg.get("heatmap_metrics", {})
                    changed_fraction = metrics.get("changed_fraction", 0) * 100
                    bbox = metrics.get("difference_bbox_px")
                    f.write("<tr>\n")
                    f.write(f"  <td><b>{display_name}</b><br>Page {page_num}</td>\n")
                    f.write(f"  <td><img src=\"images/{heatmap_img}\" width=\"760\" alt=\"{display_name} page {page_num} difference heatmap\"></td>\n")
                    f.write(
                        "  <td>"
                        f"changed: {metrics.get('changed_pixels', 0)} px ({changed_fraction:.2f}%)<br>"
                        f"bbox: {bbox}<br>"
                        f"mean abs RGB: {metrics.get('mean_abs_rgb', 0)}<br>"
                        f"RMSE RGB: {metrics.get('rmse_rgb', 0)}<br>"
                        f"threshold: {metrics.get('threshold', 0)}, gain: {metrics.get('gain', 0)}"
                        "</td>\n"
                    )
                    f.write("</tr>\n")
            f.write("</table>\n\n")

        # ── Detect whether any result has auxiliary images ───────────────
        has_auxiliary = any(
            pg.get("auxiliary_img") or pg.get("office_img")
            for r in results
            for pg in r.get("diff_images", [])
        )
        num_cols = 3 if has_auxiliary else 2
        img_width = 260 if has_auxiliary else 340

        # ── Visual side-by-side table ──────────────────────────────────────
        f.write("## Visual Comparison\n\n")
        if has_auxiliary:
            f.write(
                f"Scores compare {candidate_label} against {reference_label}. "
                f"{auxiliary_label} is an auxiliary rendering and does not affect scores.\n\n"
            )
        f.write("<table>\n")
        if has_auxiliary:
            f.write(f"<tr><th>{candidate_label}</th><th>{reference_label}</th><th>{auxiliary_label}</th></tr>\n")
        else:
            f.write(f"<tr><th>{candidate_label}</th><th>{reference_label}</th></tr>\n")

        for r in results:
            name = r["name"]
            display_name = result_display_name(r)
            metadata = result_metadata_summary(r)
            overall = r.get("overall_score", "N/A")
            if isinstance(overall, float):
                if overall >= 0.9:
                    score_cell = f'<span style="color:#3fb950">⬤</span> {overall * 100:.1f}%'
                elif overall >= 0.7:
                    score_cell = f'<span style="color:#d29922">⬤</span> {overall * 100:.1f}%'
                else:
                    score_cell = f'<span style="color:#f85149">⬤</span> {overall * 100:.1f}%'
            else:
                score_cell = str(overall)

            # Collect AI analysis entries for this case, keyed by page
            ai_by_page: dict[int, dict] = {}
            for a in r.get("ai_analysis", []):
                if not a.get("skipped") and "error" not in a:
                    ai_by_page[a.get("page", 1)] = a

            diff_images = r.get("diff_images", [])

            # Header row: test case name + score
            title = display_name if not metadata else f"{display_name}<br><small>{metadata}</small>"
            f.write(f"<tr>\n")
            f.write(f"  <td><b>{title}</b></td>\n")
            f.write(f"  <td colspan=\"{num_cols - 1}\">{display_name} {score_cell}</td>\n")
            f.write(f"</tr>\n")

            if not diff_images:
                f.write(f"<tr>\n")
                f.write(f"  <td colspan=\"{num_cols}\"><i>No images</i></td>\n")
                f.write(f"</tr>\n")
                continue

            for idx, pg in enumerate(diff_images):
                page_num = pg.get("page", idx + 1)
                mini_img = pg.get("minipdf_img")
                ref_img  = pg.get("reference_img")
                auxiliary_img = pg.get("auxiliary_img") or pg.get("office_img")
                mini_td = (f'<img src="images/{mini_img}" width="{img_width}" alt="{candidate_label}">'
                           if mini_img else "<i>missing</i>")
                ref_td  = (f'<img src="images/{ref_img}" width="{img_width}" alt="{reference_label}">'
                           if ref_img else "<i>missing</i>")

                f.write(f"<tr>\n")
                f.write(f"  <td>{mini_td}</td>\n")
                f.write(f"  <td>{ref_td}</td>\n")
                if has_auxiliary:
                    auxiliary_td = (f'<img src="images/{auxiliary_img}" width="{img_width}" alt="{auxiliary_label}">'
                                    if auxiliary_img else "<i>missing</i>")
                    f.write(f"  <td>{auxiliary_td}</td>\n")
                f.write(f"</tr>\n")

                # ── AI analysis row for this page ──────────────────────────
                ai = ai_by_page.get(page_num)
                if ai:
                    sev = ai.get("severity", "")
                    ai_score = ai.get("ai_visual_score", "")
                    sev_color = {"low": "#3fb950", "medium": "#d29922", "high": "#f85149"}.get(sev, "#8b949e")
                    sev_label = f'<span style="color:{sev_color}"><b>{sev.upper()}</b></span>'

                    diffs = ai.get("differences", [])
                    sugs  = ai.get("suggestions", [])

                    diff_html = "".join(f"<li>{d}</li>" for d in diffs) if diffs else "<li><i>none</i></li>"
                    sug_html  = "".join(f"<li>{s}</li>" for s in sugs)  if sugs  else "<li><i>none</i></li>"

                    f.write("<tr>\n")
                    f.write(
                        f"  <td colspan=\"{num_cols}\" style=\"background:#0d1117;padding:8px 12px;\">\n"
                        f"    <details open>\n"
                        f"      <summary>🤖 AI Analysis &nbsp;·&nbsp; severity: {sev_label} &nbsp;·&nbsp; "
                        f"AI visual score: <b>{ai_score}</b></summary>\n"
                        f"      <br>\n"
                        f"      <b>Differences detected:</b>\n"
                        f"      <ul style=\"margin:4px 0 8px\">{diff_html}</ul>\n"
                        f"      <b>Suggestions:</b>\n"
                        f"      <ul style=\"margin:4px 0 4px\">{sug_html}</ul>\n"
                        f"    </details>\n"
                        f"  </td>\n"
                    )
                    f.write("</tr>\n")

        f.write("</table>\n\n")

        # ── Detailed sections ──────────────────────────────────────────────────
        f.write("## Detailed Results\n\n")
        for r in results:
            name = r["name"]
            display_name = result_display_name(r)
            metadata = result_metadata_summary(r)
            f.write(f"### {display_name}\n\n")

            if "error" in r:
                f.write(f"**Error:** {r['error']}\n\n")
                continue

            if metadata:
                f.write(f"- **Case Metadata:** {metadata}\n")
            if r.get("source_path"):
                f.write(f"- **Source:** {r['source_path']}\n")
            f.write(f"- **Text Similarity:** {r.get('text_similarity', 'N/A')}\n")
            f.write(f"- **Visual Average:** {r.get('visual_avg', 'N/A')}\n")
            if r.get("ai_visual_avg") is not None:
                f.write(f"- **AI Visual Score:** {r['ai_visual_avg']}\n")
            f.write(f"- **Overall Score:** {r.get('overall_score', 'N/A')}\n")
            f.write(f"- **Pages:** MiniPdf={r.get('minipdf_pages', '?')}, Reference={r.get('reference_pages', '?')}\n")
            f.write(f"- **File Size:** MiniPdf={r.get('minipdf_size', '?')} bytes, Reference={r.get('reference_size', '?')} bytes\n\n")

            diff = r.get("text_diff", "")
            if diff and diff != "(identical)":
                f.write("<details><summary>Text Diff</summary>\n\n```diff\n")
                # Truncate very long diffs
                if len(diff) > 3000:
                    f.write(diff[:3000])
                    f.write(f"\n... ({len(diff) - 3000} more characters)\n")
                else:
                    f.write(diff)
                f.write("\n```\n</details>\n\n")
            else:
                f.write("Text content: ✅ Identical\n\n")

        # Improvement suggestions
        f.write("## Improvement Suggestions\n\n")

        # AI-generated suggestions (aggregated across all test cases)
        all_ai_suggestions: list[tuple[str, str]] = []  # (test_name, suggestion)
        all_ai_differences: list[tuple[str, str]] = []  # (test_name, difference)
        for r in results:
            for ai in r.get("ai_analysis", []):
                if "error" in ai or ai.get("skipped"):
                    continue
                for s in ai.get("suggestions", []):
                    all_ai_suggestions.append((r["name"], s))
                for d in ai.get("differences", []):
                    all_ai_differences.append((r["name"], d))

        if all_ai_differences:
            f.write("### 🤖 AI Visual Analysis Findings\n\n")
            # Deduplicate by lowercased text to compress repetitive findings
            seen: set[str] = set()
            for test_name, diff in all_ai_differences:
                key = diff.lower()[:80]
                if key not in seen:
                    seen.add(key)
                    f.write(f"- **[{test_name}]** {diff}\n")
            f.write("\n")

        if all_ai_suggestions:
            f.write("### 🤖 AI-Recommended Code Improvements\n\n")
            seen_s: set[str] = set()
            for test_name, sug in all_ai_suggestions:
                key = sug.lower()[:80]
                if key not in seen_s:
                    seen_s.add(key)
                    f.write(f"- **[{test_name}]** {sug}\n")
            f.write("\n")

        # Per-case AI analysis blocks
        has_any_ai = any(r.get("ai_analysis") for r in results)
        if has_any_ai:
            f.write("### AI Analysis Per Test Case\n\n")
            for r in results:
                for ai in r.get("ai_analysis", []):
                    if ai.get("skipped"):
                        continue
                    if "error" in ai:
                        f.write(f"- **{r['name']} p{ai['page']}**: ⚠ {ai['error']}\n")
                        continue
                    severity_icon = {"low": "🟢", "medium": "🟡", "high": "🔴"}.get(ai.get("severity", ""), "⚪")
                    f.write(f"<details><summary>{severity_icon} {r['name']} — Page {ai['page']} "
                            f"(AI score: {ai.get('ai_visual_score', 'N/A')}, "
                            f"severity: {ai.get('severity', 'N/A')})</summary>\n\n")
                    if ai.get("differences"):
                        f.write("**Differences:**\n")
                        for d in ai["differences"]:
                            f.write(f"- {d}\n")
                        f.write("\n")
                    if ai.get("suggestions"):
                        f.write("**Suggestions:**\n")
                        for s in ai["suggestions"]:
                            f.write(f"- {s}\n")
                        f.write("\n")
                    f.write("</details>\n\n")

        # Classic score-based suggestions
        low_scores = [(r["name"], r.get("overall_score", 0)) for r in results if r.get("overall_score", 1) < 0.8]
        if low_scores:
            low_scores.sort(key=lambda x: x[1])
            f.write("### ⚠ Low-Score Test Cases (below 0.8)\n\n")
            for name, score in low_scores:
                f.write(f"1. **{name}** (score: {score})\n")
            if not all_ai_suggestions:
                f.write("\nReview the text diffs and visual comparisons above to identify specific rendering issues.\n")
        elif not all_ai_suggestions:
            f.write("All test cases scored 0.8 or above. 🎉\n")
        elif not low_scores:
            f.write("\n✅ All test cases scored 0.8 or above.\n")

    print(f"\nReports saved:")
    print(f"  Markdown: {md_path}")
    print(f"  JSON:     {json_path}")


def main():
    parser = argparse.ArgumentParser(description="Compare MiniPdf PDFs against reference PDFs")
    parser.add_argument("--minipdf-dir", default=os.path.join("..", "MiniPdf.Scripts", "pdf_output"),
                        help="Directory containing MiniPdf-generated PDFs")
    parser.add_argument("--reference-dir", default="reference_pdfs",
                        help="Directory containing reference PDFs (from LibreOffice)")
    parser.add_argument("--office-dir", default=None,
                        help=argparse.SUPPRESS)
    parser.add_argument("--auxiliary-dir", default=None,
                        help="Directory containing an optional secondary reference rendering")
    parser.add_argument("--report-dir", default="reports",
                        help="Output directory for comparison reports")
    # AI comparison options
    parser.add_argument("--ai-compare", action="store_true",
                        help="Enable AI-based visual comparison via OpenAI / Azure OpenAI vision")
    parser.add_argument("--ai-max-pages", type=int, default=1, metavar="N",
                        help="Maximum number of pages per PDF to send to the AI (default: 1)")
    parser.add_argument("--ai-threshold", type=float, default=0.97, metavar="T",
                        help="Skip AI call when pixel similarity is already above this threshold (default: 0.97)")
    parser.add_argument("--report-only", action="store_true",
                        help="Skip comparisons; regenerate report from existing comparison_report.json")
    parser.add_argument("--filter", default=None, metavar="PATTERN",
                        help="Only compare files whose name contains this substring")
    parser.add_argument("--max-pages", type=int, default=0, metavar="N",
                        help="Compare content and visuals for at most N pages per PDF; 0 compares all pages")
    parser.add_argument("--manifest", default=None, metavar="JSON",
                        help="Benchmark manifest JSON. When set, compare exactly the listed cases instead of scanning directories")
    parser.add_argument("--report-scope", default="shared", metavar="NAME",
                        help="Logical report audience/scope recorded in JSON metadata (default: shared)")
    parser.add_argument("--composite-images", action="store_true",
                        help="Also write labeled side-by-side composite PNGs under the report directory")
    parser.add_argument("--composite-dir", default=None, metavar="DIR",
                        help="Composite image output directory (default: <report-dir>/side-by-side)")
    parser.add_argument("--heatmaps", action="store_true",
                        help="Generate contextual per-page pixel-difference heatmaps")
    parser.add_argument("--heatmap-threshold", type=int, default=12, metavar="N",
                        help="Ignore per-channel differences at or below this value (default: 12)")
    parser.add_argument("--heatmap-gain", type=float, default=5.0, metavar="G",
                        help="Amplification applied above the heatmap threshold (default: 5.0)")
    parser.add_argument("--candidate-label", default="MiniPdf",
                        help="Label for candidate renderer images in composite output")
    parser.add_argument("--reference-label", default="LibreOffice Reference",
                        help="Label for reference renderer images in composite output")
    parser.add_argument("--office-label", default="Office",
                        help=argparse.SUPPRESS)
    parser.add_argument("--auxiliary-label", default=None,
                        help="Label for optional secondary reference images in report output")
    args = parser.parse_args()

    if args.heatmaps:
        try:
            import PIL  # noqa: F401
        except ImportError:
            print("WARNING: --heatmaps requested but Pillow is not installed.")
            print("         Install with: pip install Pillow")

    if args.ai_compare:
        if not HAS_OPENAI:
            print("WARNING: --ai-compare requested but 'openai' package is not installed.")
            print("         Install with: pip install openai")
        elif AI_CLIENT is None:
            print("WARNING: --ai-compare requested but no API credentials found.")
            print("         Set OPENAI_API_KEY  OR  AZURE_OPENAI_ENDPOINT + AZURE_OPENAI_KEY.")
        else:
            source = "Azure OpenAI" if os.environ.get("AZURE_OPENAI_ENDPOINT") else "OpenAI"
            print(f"AI comparison enabled  ({source}, model={AI_MODEL})")

    minipdf_dir = os.path.abspath(args.minipdf_dir)
    reference_dir = os.path.abspath(args.reference_dir)
    auxiliary_dir_arg = args.auxiliary_dir or args.office_dir
    auxiliary_dir = os.path.abspath(auxiliary_dir_arg) if auxiliary_dir_arg else None
    auxiliary_label = args.auxiliary_label or args.office_label
    report_dir = os.path.abspath(args.report_dir)
    images_dir = os.path.join(report_dir, "images")
    composite_dir = os.path.abspath(args.composite_dir) if args.composite_dir else os.path.join(report_dir, "side-by-side")
    labels = {
        "candidate": args.candidate_label,
        "reference": args.reference_label,
        "auxiliary": auxiliary_label,
    }

    os.makedirs(report_dir, exist_ok=True)
    json_path = os.path.join(report_dir, "comparison_report.json")

    # ── Report-only mode: regenerate MD from existing JSON ─────────────────
    if args.report_only:
        json_path = os.path.join(report_dir, "comparison_report.json")
        if not os.path.isfile(json_path):
            print(f"ERROR: {json_path} not found. Run without --report-only first.")
            sys.exit(1)
        with open(json_path, encoding="utf-8") as jf:
            results = json.load(jf)
        print(f"Loaded {len(results)} results from {json_path}")
        generate_report(results, report_dir, labels)
        avg = sum(r.get("overall_score", 0) for r in results) / len(results) if results else 0
        print(f"Report regenerated. Overall avg score: {avg:.4f}")
        return

    print(f"MiniPdf PDFs:    {minipdf_dir}")
    print(f"Reference PDFs:  {reference_dir}")
    if auxiliary_dir:
        print(f"Auxiliary PDFs:  {auxiliary_dir}")
    print(f"Report output:   {report_dir}")
    if args.manifest:
        print(f"Manifest:        {os.path.abspath(args.manifest)}")
        print(f"Report scope:    {args.report_scope}")
    if args.composite_images:
        print(f"Composite PNGs:  {composite_dir}")
    if args.heatmaps:
        print(f"Heatmaps:        threshold={args.heatmap_threshold}, gain={args.heatmap_gain:g}")
    print()

    if args.manifest:
        cases = [case for case in load_manifest_cases(args.manifest) if case_matches_filter(case, args.filter)]
    else:
        # Collect all test names from both directories
        names = set()
        for d in [minipdf_dir, reference_dir]:
            if os.path.isdir(d):
                for f in Path(d).glob("*.pdf"):
                    names.add(f.stem)
        if auxiliary_dir and os.path.isdir(auxiliary_dir):
            for f in Path(auxiliary_dir).glob("*.pdf"):
                names.add(f.stem)

        # Apply filter
        if args.filter:
            names = {n for n in names if args.filter.lower() in n.lower()}
        cases = [{"name": name} for name in sorted(names, key=natural_sort_key)]

    if not cases:
        print("No PDF files found in either directory.")
        print("Run the following first:")
        print("  1. python generate_classic_xlsx.py       (generate test Excel files)")
        print("  2. dotnet run convert_xlsx_to_pdf.cs      (generate MiniPdf PDFs)")
        print("  3. python generate_reference_pdfs.py      (generate reference PDFs)")
        sys.exit(1)

    filtered_mode = bool(args.filter)
    existing_results_by_name = {}
    if filtered_mode and os.path.isfile(json_path):
        try:
            with open(json_path, encoding="utf-8") as jf:
                existing_results = json.load(jf)
            if isinstance(existing_results, list):
                for r in existing_results:
                    if isinstance(r, dict) and r.get("name"):
                        existing_results_by_name[r["name"]] = r
            print(f"Filtered comparison mode: loaded {len(existing_results_by_name)} existing results to preserve.")
        except Exception as e:
            print(f"WARNING: Failed to load existing report for merge: {e}")

    results = []
    for case in sorted(cases, key=lambda c: natural_sort_key(c["name"])):
        name = case["name"]
        mp = os.path.join(minipdf_dir, f"{name}.pdf")
        rp = os.path.join(reference_dir, f"{name}.pdf")
        auxiliary_path = os.path.join(auxiliary_dir, f"{name}.pdf") if auxiliary_dir else None
        print(f"Comparing: {name} ...", end=" ")
        result = compare_single(
            mp, rp, images_dir, name,
            ai_compare=args.ai_compare,
            ai_max_pages=args.ai_max_pages,
            ai_threshold=args.ai_threshold,
            auxiliary_path=auxiliary_path,
            case_metadata=case,
            report_scope=args.report_scope if args.manifest else None,
            composite_images=args.composite_images,
            composite_output_dir=composite_dir,
            labels=labels,
            heatmaps=args.heatmaps,
            heatmap_threshold=args.heatmap_threshold,
            heatmap_gain=args.heatmap_gain,
            max_compare_pages=args.max_pages,
        )
        score = result.get("overall_score", "N/A")
        print(f"score={score}")
        results.append(result)

    final_results = results
    if filtered_mode and existing_results_by_name:
        for r in results:
            existing_results_by_name[r["name"]] = r
        # Keep historical order from existing report; only update touched cases.
        existing_order = []
        try:
            with open(json_path, encoding="utf-8") as jf:
                existing_results = json.load(jf)
            if isinstance(existing_results, list):
                existing_order = [r.get("name") for r in existing_results if isinstance(r, dict) and r.get("name")]
        except Exception:
            existing_order = []

        final_results = []
        seen = set()
        for name in existing_order:
            if name in existing_results_by_name and name not in seen:
                final_results.append(existing_results_by_name[name])
                seen.add(name)

        # Append newly introduced names (if any) using natural order.
        for name in sorted(existing_results_by_name.keys(), key=natural_sort_key):
            if name not in seen:
                final_results.append(existing_results_by_name[name])
                seen.add(name)
        print(
            f"Merged filtered results: updated {len(results)} case(s), "
            f"preserved {len(final_results) - len(results)} existing case(s)."
        )
    else:
        final_results = sorted(final_results, key=lambda r: natural_sort_key(r.get("name", "")))

    generate_report(final_results, report_dir, labels)

    # Print summary
    avg = sum(r.get("overall_score", 0) for r in final_results) / len(final_results) if final_results else 0
    print(f"\n{'='*60}")
    print(f"Overall Average Score: {avg:.4f}")
    print(f"Total Cases In Report: {len(final_results)}")
    print(f"{'='*60}")

    if avg < 0.7:
        print("⚠ Many test cases are significantly different from the reference.")
        print("  Check the report for details and improvement suggestions.")


if __name__ == "__main__":
    main()

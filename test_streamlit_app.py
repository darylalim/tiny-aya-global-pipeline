# SPDX-License-Identifier: Apache-2.0
import os
import tomllib
from pathlib import Path
from typing import Any
from unittest.mock import MagicMock, patch

import streamlit_app
from streamlit_app import (
    LANGUAGES,
    build_translation_prompt,
    chunk_document,
    chunk_text,
    clean_model_output,
    count_tokens,
    docling_available,
    heading_level,
    liteparse_available,
    load_document,
    load_document_markdown,
    render_output,
    split_oversized,
    stream_translate,
    token_overhead,
    tokenize_prompt,
    translate_document,
)

# -- module configuration ------------------------------------------------------


def test_transformers_verbosity_is_set() -> None:
    # setdefault preserves an existing override, so assert only that it's set.
    assert os.environ.get("TRANSFORMERS_VERBOSITY")


# -- streamlit_app.py width API ------------------------------------------------

_APP_SOURCE = (Path(__file__).parent / "streamlit_app.py").read_text(encoding="utf-8")


def test_no_deprecated_use_container_width() -> None:
    # use_container_width is deprecated in Streamlit 1.58; guard against
    # reintroducing it after the migration to the width API.
    assert "use_container_width" not in _APP_SOURCE


def test_buttons_use_width_stretch() -> None:
    # The five full-width controls (swap, translate, download, translate_doc,
    # download_doc) set width="stretch".
    assert _APP_SOURCE.count('width="stretch"') == 5


# -- streamlit_app.py shared UI constants --------------------------------------


def test_panel_height_not_hardcoded() -> None:
    # The 450px panel height now lives in PANEL_HEIGHT; guard against re-inlining
    # the magic number at a call site (text_area panels or render_output).
    assert "height=450" not in _APP_SOURCE


def test_warning_strings_defined_once() -> None:
    # Each shared warning lives in exactly one place — its module-level constant.
    # The Text- and Document-tab call sites reference SAME_LANGUAGE_WARNING /
    # NO_OUTPUT_WARNING, so neither raw literal should be duplicated.
    assert _APP_SOURCE.count('"Please pick two different languages."') == 1
    assert _APP_SOURCE.count('"Model produced no output."') == 1


# -- streamlit_app.py page config ----------------------------------------------


def test_set_page_config_sets_title_icon_and_wide_layout() -> None:
    # set_page_config must be the first Streamlit command; it defines the
    # browser-tab title, favicon, and the wide layout for the side-by-side panels.
    assert "st.set_page_config(" in _APP_SOURCE
    assert 'page_title="Tiny Aya Translate"' in _APP_SOURCE
    assert 'page_icon=":material/translate:"' in _APP_SOURCE
    assert 'layout="wide"' in _APP_SOURCE


# -- .streamlit/config.toml theme ----------------------------------------------

_CONFIG_PATH = Path(__file__).parent / ".streamlit" / "config.toml"


def _load_theme_config() -> dict[str, Any]:
    with _CONFIG_PATH.open("rb") as f:
        return tomllib.load(f)


def test_theme_config_exists() -> None:
    assert _CONFIG_PATH.is_file()


def test_theme_config_has_theme_section() -> None:
    assert "theme" in _load_theme_config()


def test_theme_config_defines_light_and_dark_modes() -> None:
    # Both variants must exist for Streamlit to show the light/dark switch;
    # a lone [theme] section would lock the app to a single mode.
    theme = _load_theme_config()["theme"]
    assert "light" in theme
    assert "dark" in theme


def _relative_luminance(hex_color: str) -> float:
    r, g, b = (int(hex_color[i : i + 2], 16) / 255 for i in (1, 3, 5))

    def _lin(c: float) -> float:
        return c / 12.92 if c <= 0.03928 else ((c + 0.055) / 1.055) ** 2.4

    return 0.2126 * _lin(r) + 0.7152 * _lin(g) + 0.0722 * _lin(b)


def _contrast_ratio(hex_a: str, hex_b: str) -> float:
    lum_a, lum_b = _relative_luminance(hex_a), _relative_luminance(hex_b)
    lighter, darker = max(lum_a, lum_b), min(lum_a, lum_b)
    return (lighter + 0.05) / (darker + 0.05)


def test_primary_button_text_readable_in_both_modes() -> None:
    # Streamlit renders primary-button labels white at body size, so
    # white-on-primaryColor must clear WCAG AA for normal text (4.5:1). Guards
    # against a light accent like the old dark-mode #88c0d0 (~2:1).
    theme = _load_theme_config()["theme"]
    for mode in ("light", "dark"):
        primary = theme[mode]["primaryColor"]
        ratio = _contrast_ratio("#ffffff", primary)
        assert ratio >= 4.5, f"{mode} primaryColor {primary} contrast {ratio:.2f}"


def test_link_text_readable_in_both_modes() -> None:
    # linkColor is body-size text on the page background, so it must clear WCAG
    # AA for normal text (4.5:1) in both modes.
    theme = _load_theme_config()["theme"]
    for mode in ("light", "dark"):
        link = theme[mode]["linkColor"]
        bg = theme[mode]["backgroundColor"]
        ratio = _contrast_ratio(link, bg)
        assert ratio >= 4.5, f"{mode} linkColor {link} on {bg} contrast {ratio:.2f}"


# -- LANGUAGES -----------------------------------------------------------------


def test_languages_list_has_67_entries() -> None:
    assert len(LANGUAGES) == 67


def test_languages_list_contains_english() -> None:
    assert "English" in LANGUAGES


def test_languages_list_contains_japanese() -> None:
    assert "Japanese" in LANGUAGES


# -- build_translation_prompt --------------------------------------------------


def test_build_translation_prompt_returns_single_message() -> None:
    result = build_translation_prompt("Hello", "English", "French")
    assert len(result) == 1
    assert result[0]["role"] == "user"


def test_build_translation_prompt_contains_languages() -> None:
    result = build_translation_prompt("Hello", "English", "French")
    content = result[0]["content"]
    assert "English" in content
    assert "French" in content


def test_build_translation_prompt_contains_text() -> None:
    result = build_translation_prompt("Good morning", "English", "Spanish")
    content = result[0]["content"]
    assert "Good morning" in content


def test_build_translation_prompt_instruction() -> None:
    result = build_translation_prompt("Hello", "English", "French")
    content = result[0]["content"]
    assert "Translate" in content
    assert "Output only the translation" in content


# -- tokenize_prompt -----------------------------------------------------------


def test_tokenize_prompt_returns_token_ids() -> None:
    mock_tokenizer = MagicMock()
    mock_tokenizer.apply_chat_template.return_value = [1, 2, 3, 4, 5]

    assert tokenize_prompt("Hello", "English", "French", mock_tokenizer) == [
        1,
        2,
        3,
        4,
        5,
    ]


def test_tokenize_prompt_calls_apply_chat_template_with_tokenize_true() -> None:
    mock_tokenizer = MagicMock()
    mock_tokenizer.apply_chat_template.return_value = [1, 2, 3]

    tokenize_prompt("Hello", "English", "French", mock_tokenizer)

    call_kwargs = mock_tokenizer.apply_chat_template.call_args.kwargs
    assert call_kwargs["tokenize"] is True
    assert call_kwargs["add_generation_prompt"] is True


def test_tokenize_prompt_uses_translation_prompt() -> None:
    mock_tokenizer = MagicMock()
    mock_tokenizer.apply_chat_template.return_value = [1]

    tokenize_prompt("Good morning", "English", "Spanish", mock_tokenizer)

    messages = mock_tokenizer.apply_chat_template.call_args[0][0]
    assert len(messages) == 1
    content = messages[0]["content"]
    assert "English" in content
    assert "Spanish" in content
    assert "Good morning" in content


# -- clean_model_output --------------------------------------------------------


def test_clean_model_output_strips_whitespace() -> None:
    assert clean_model_output("  Hello world  ") == "Hello world"


def test_clean_model_output_empty_string() -> None:
    assert clean_model_output("") == ""


def test_clean_model_output_newlines() -> None:
    assert clean_model_output("\n\nBonjour\n\n") == "Bonjour"


def test_clean_model_output_preserves_inner_whitespace() -> None:
    assert clean_model_output("  Hello   world  ") == "Hello   world"


def test_clean_model_output_strips_end_response_token() -> None:
    assert clean_model_output("Bonjour le monde<|END_RESPONSE|>") == "Bonjour le monde"


def test_clean_model_output_strips_end_response_token_with_whitespace() -> None:
    assert (
        clean_model_output("  Bonjour le monde  <|END_RESPONSE|>  ")
        == "Bonjour le monde"
    )


# -- stream_translate ----------------------------------------------------------


def _make_chunk(text: str) -> MagicMock:
    chunk = MagicMock()
    chunk.text = text
    return chunk


@patch("mlx_lm.stream_generate")
def test_stream_translate_yields_cleaned_partials(
    mock_stream_generate: MagicMock,
) -> None:
    mock_stream_generate.return_value = iter([_make_chunk("Bon"), _make_chunk("jour")])

    results = list(
        stream_translate(
            prompt_ids=[1, 2, 3],
            model=MagicMock(),
            tokenizer=MagicMock(),
        )
    )
    assert results == ["Bon", "Bonjour"]


@patch("mlx_lm.stream_generate")
def test_stream_translate_handles_empty_stream(
    mock_stream_generate: MagicMock,
) -> None:
    mock_stream_generate.return_value = iter([])

    results = list(
        stream_translate(
            prompt_ids=[1, 2, 3],
            model=MagicMock(),
            tokenizer=MagicMock(),
        )
    )
    assert results == []


@patch("mlx_lm.stream_generate")
def test_stream_translate_strips_end_response_token_mid_stream(
    mock_stream_generate: MagicMock,
) -> None:
    mock_stream_generate.return_value = iter(
        [_make_chunk("Bonjour"), _make_chunk("<|END_RESPONSE|>")]
    )

    results = list(
        stream_translate(
            prompt_ids=[1, 2, 3],
            model=MagicMock(),
            tokenizer=MagicMock(),
        )
    )
    assert results == ["Bonjour", "Bonjour"]


@patch("mlx_lm.stream_generate")
@patch("mlx_lm.sample_utils.make_sampler")
def test_stream_translate_calls_stream_generate_with_correct_params(
    mock_make_sampler: MagicMock,
    mock_stream_generate: MagicMock,
) -> None:
    mock_stream_generate.return_value = iter([_make_chunk("Bonjour")])
    mock_make_sampler.return_value = MagicMock()

    list(
        stream_translate(
            prompt_ids=[1, 2, 3, 4, 5],
            model=MagicMock(),
            tokenizer=MagicMock(),
            temperature=0.3,
            max_tokens=500,
        )
    )

    mock_make_sampler.assert_called_once_with(temp=0.3)
    mock_stream_generate.assert_called_once()
    call_kwargs = mock_stream_generate.call_args.kwargs
    assert call_kwargs["prompt"] == [1, 2, 3, 4, 5]
    assert call_kwargs["max_tokens"] == 500
    assert call_kwargs["sampler"] is mock_make_sampler.return_value


@patch("mlx_lm.stream_generate")
def test_stream_translate_does_not_retokenize(
    mock_stream_generate: MagicMock,
) -> None:
    mock_stream_generate.return_value = iter([_make_chunk("Bonjour")])
    mock_tokenizer = MagicMock()

    list(
        stream_translate(
            prompt_ids=[1, 2, 3],
            model=MagicMock(),
            tokenizer=mock_tokenizer,
        )
    )

    mock_tokenizer.apply_chat_template.assert_not_called()


@patch("mlx_lm.stream_generate")
@patch("mlx_lm.sample_utils.make_sampler")
def test_stream_translate_uses_default_params(
    mock_make_sampler: MagicMock,
    mock_stream_generate: MagicMock,
) -> None:
    mock_stream_generate.return_value = iter([_make_chunk("Bonjour")])
    mock_make_sampler.return_value = MagicMock()

    list(
        stream_translate(
            prompt_ids=[1, 2, 3],
            model=MagicMock(),
            tokenizer=MagicMock(),
        )
    )

    mock_make_sampler.assert_called_once_with(temp=streamlit_app.DEFAULT_TEMPERATURE)
    assert (
        mock_stream_generate.call_args.kwargs["max_tokens"]
        == streamlit_app.DEFAULT_MAX_TOKENS
    )


# -- docling_available ---------------------------------------------------------


@patch("importlib.util.find_spec")
def test_docling_available_true_when_spec_found(mock_find_spec: MagicMock) -> None:
    mock_find_spec.return_value = object()
    assert docling_available() is True


@patch("importlib.util.find_spec")
def test_docling_available_false_when_spec_missing(
    mock_find_spec: MagicMock,
) -> None:
    mock_find_spec.return_value = None
    assert docling_available() is False


# -- load_document -------------------------------------------------------------


@patch("docling.document_converter.DocumentConverter")
def test_load_document_returns_converted_document(
    mock_converter_cls: MagicMock,
) -> None:
    expected_doc = MagicMock()
    mock_converter_cls.return_value.convert.return_value.document = expected_doc

    assert load_document(b"file bytes", "sample.pdf") is expected_doc


@patch("docling.document_converter.DocumentConverter")
def test_load_document_builds_stream_with_filename(
    mock_converter_cls: MagicMock,
) -> None:
    load_document(b"data", "report.docx")

    source = mock_converter_cls.return_value.convert.call_args[0][0]
    assert source.name == "report.docx"


@patch("docling.document_converter.DocumentConverter")
def test_load_document_passes_file_bytes_to_stream(
    mock_converter_cls: MagicMock,
) -> None:
    load_document(b"hello bytes", "notes.html")

    source = mock_converter_cls.return_value.convert.call_args[0][0]
    assert source.stream.getvalue() == b"hello bytes"


# -- chunk_document ------------------------------------------------------------


@patch("docling.chunking.HybridChunker")
@patch("docling_core.transforms.chunker.tokenizer.huggingface.HuggingFaceTokenizer")
def test_chunk_document_returns_contextualized_strings(
    mock_hf_tokenizer: MagicMock, mock_hybrid_chunker_cls: MagicMock
) -> None:
    chunker = mock_hybrid_chunker_cls.return_value
    chunker.chunk.return_value = ["raw_a", "raw_b"]
    chunker.contextualize.side_effect = ["context A", "context B"]

    result = chunk_document(MagicMock(), MagicMock())

    assert result == ["context A", "context B"]


@patch("docling.chunking.HybridChunker")
@patch("docling_core.transforms.chunker.tokenizer.huggingface.HuggingFaceTokenizer")
def test_chunk_document_handles_empty_document(
    mock_hf_tokenizer: MagicMock, mock_hybrid_chunker_cls: MagicMock
) -> None:
    mock_hybrid_chunker_cls.return_value.chunk.return_value = []

    assert chunk_document(MagicMock(), MagicMock()) == []


@patch("docling.chunking.HybridChunker")
@patch("docling_core.transforms.chunker.tokenizer.huggingface.HuggingFaceTokenizer")
def test_chunk_document_passes_max_tokens_to_tokenizer(
    mock_hf_tokenizer: MagicMock, mock_hybrid_chunker_cls: MagicMock
) -> None:
    mock_hybrid_chunker_cls.return_value.chunk.return_value = []

    chunk_document(MagicMock(), MagicMock(), max_tokens=1234)

    assert mock_hf_tokenizer.call_args.kwargs["max_tokens"] == 1234


@patch("docling.chunking.HybridChunker")
@patch("docling_core.transforms.chunker.tokenizer.huggingface.HuggingFaceTokenizer")
def test_chunk_document_defaults_to_max_chunk_tokens(
    mock_hf_tokenizer: MagicMock, mock_hybrid_chunker_cls: MagicMock
) -> None:
    mock_hybrid_chunker_cls.return_value.chunk.return_value = []

    chunk_document(MagicMock(), MagicMock())

    assert (
        mock_hf_tokenizer.call_args.kwargs["max_tokens"]
        == streamlit_app.MAX_CHUNK_TOKENS
    )


# -- liteparse_available -------------------------------------------------------


@patch("importlib.util.find_spec")
def test_liteparse_available_true_when_spec_found(mock_find_spec: MagicMock) -> None:
    mock_find_spec.return_value = object()
    assert liteparse_available() is True


@patch("importlib.util.find_spec")
def test_liteparse_available_false_when_spec_missing(
    mock_find_spec: MagicMock,
) -> None:
    mock_find_spec.return_value = None
    assert liteparse_available() is False


# -- load_document_markdown ----------------------------------------------------


@patch("liteparse.LiteParse")
def test_load_document_markdown_returns_parsed_text(
    mock_liteparse_cls: MagicMock,
) -> None:
    mock_liteparse_cls.return_value.parse.return_value.text = "# Title\n\nBody."

    assert load_document_markdown(b"pdf bytes") == "# Title\n\nBody."
    mock_liteparse_cls.return_value.parse.assert_called_once_with(b"pdf bytes")


@patch("liteparse.LiteParse")
def test_load_document_markdown_requests_quiet_markdown_without_ocr(
    mock_liteparse_cls: MagicMock,
) -> None:
    load_document_markdown(b"data")

    kwargs = mock_liteparse_cls.call_args.kwargs
    assert kwargs["output_format"] == "markdown"
    # OCR off: born-digital PDFs already carry a text layer. quiet: LiteParse
    # otherwise prints timing lines into Streamlit's stdout.
    assert kwargs["ocr_enabled"] is False
    assert kwargs["quiet"] is True


# -- heading_level -------------------------------------------------------------


def test_heading_level_reads_atx_depth() -> None:
    assert heading_level("# Title") == 1
    assert heading_level("### Section") == 3
    assert heading_level("###### Deepest") == 6


def test_heading_level_zero_for_non_headings() -> None:
    assert heading_level("Just a paragraph.") == 0
    assert heading_level("") == 0
    # Seven hashes is past the ATX limit, and #tag has no space delimiter.
    assert heading_level("####### Too deep") == 0
    assert heading_level("#hashtag not a heading") == 0


# -- chunk_text ----------------------------------------------------------------


class FakeTokenizer:
    """Whitespace tokenizer so chunk_text budgets are readable in tests."""

    def encode(self, text: str) -> list[str]:
        return text.split()

    def decode(self, ids: list[str]) -> str:
        return " ".join(ids)


class SpecialTokenTokenizer:
    """Whitespace tokenizer that mimics the model tokenizer's quirks.

    The real tokenizer prepends a BOS token to every ``encode`` call and spends
    a token on a blank line. Both make an assembled chunk cost more than the sum
    of its blocks, which is what pushed chunks over budget before the packer
    charged for separators and measured the finished chunk. ``decode`` leaves
    the BOS visible so a leaked special token fails a test loudly.
    """

    def encode(self, text: str) -> list[str]:
        tokens: list[str] = []
        for i, part in enumerate(text.split("\n\n")):
            if i:
                tokens.append("\n\n")
            tokens.extend(part.split())
        return ["<bos>", *tokens]

    def decode(self, ids: list[str]) -> str:
        return " ".join(ids)


def _tok_len(text: str) -> int:
    return len(FakeTokenizer().encode(text))


def test_chunk_text_returns_empty_for_blank_input() -> None:
    assert chunk_text("", FakeTokenizer()) == []
    assert chunk_text("   \n\n  \n", FakeTokenizer()) == []


def test_chunk_text_keeps_every_chunk_within_budget() -> None:
    text = "\n\n".join(
        ["# Report", "alpha " * 20, "## Section", "beta " * 30, "gamma " * 25]
    )
    for budget in (10, 25, 60):
        chunks = chunk_text(text, FakeTokenizer(), max_tokens=budget)
        assert chunks, f"budget {budget} produced no chunks"
        assert all(_tok_len(c) <= budget for c in chunks), f"over budget at {budget}"


def test_chunk_text_packs_multiple_paragraphs_into_one_chunk() -> None:
    # Three short paragraphs fit in one generous chunk; packing greedily keeps
    # the chunk count (and so the per-chunk prompt overhead) down.
    text = "one two three\n\nfour five six\n\nseven eight nine"

    assert len(chunk_text(text, FakeTokenizer(), max_tokens=100)) == 1


def test_chunk_text_does_not_split_a_paragraph_that_fits() -> None:
    text = "alpha beta gamma\n\ndelta epsilon zeta"
    chunks = chunk_text(text, FakeTokenizer(), max_tokens=3)

    assert "alpha beta gamma" in chunks
    assert "delta epsilon zeta" in chunks


def test_chunk_text_prepends_enclosing_heading_context() -> None:
    text = "# Report\n\n## Findings\n\n" + "word " * 30
    chunks = chunk_text(text, FakeTokenizer(), max_tokens=20)

    # The body chunk carries the headings it sits under, because each chunk is
    # translated as an independent prompt with no memory of its neighbours.
    body = [c for c in chunks if "word" in c]
    assert body
    assert all(c.startswith("# Report\n\n## Findings") for c in body)


def test_chunk_text_does_not_duplicate_heading_it_opens_with() -> None:
    text = "# Report\n\nbody text here"
    chunks = chunk_text(text, FakeTokenizer(), max_tokens=100)

    assert chunks[0].count("# Report") == 1


def test_chunk_text_uses_enclosing_heading_not_the_following_one() -> None:
    # Regression: the heading trail advances as blocks are read, so a chunk
    # flushed after a later heading was seen must still carry the heading of
    # the section it actually belongs to -- not the next section's.
    text = "## First\n\naaa bbb ccc\n\n## Second\n\nddd eee fff"
    chunks = chunk_text(text, FakeTokenizer(), max_tokens=6)

    first = next(c for c in chunks if "aaa bbb ccc" in c)
    assert "## First" in first
    assert "## Second" not in first


def test_chunk_text_deeper_heading_replaces_sibling_shallower_survives() -> None:
    text = "# Book\n\n## Alpha\n\n## Beta\n\n" + "tail " * 20
    chunks = chunk_text(text, FakeTokenizer(), max_tokens=12)

    tail = next(c for c in chunks if "tail" in c)
    assert "# Book" in tail
    assert "## Beta" in tail
    # Alpha was replaced by its sibling Beta, so it must not linger in context.
    assert "## Alpha" not in tail


def test_chunk_text_splits_oversized_paragraph_on_sentence_boundaries() -> None:
    text = "First sentence here. Second sentence here. Third sentence here."
    chunks = chunk_text(text, FakeTokenizer(), max_tokens=4)

    assert len(chunks) > 1
    # Sentences stay intact rather than being cut mid-clause.
    assert all(c.strip().endswith(".") for c in chunks)


def test_chunk_text_hard_splits_a_single_unpunctuated_run() -> None:
    text = " ".join(f"w{i}" for i in range(20))
    chunks = chunk_text(text, FakeTokenizer(), max_tokens=6)

    assert len(chunks) > 1
    assert all(_tok_len(c) <= 6 for c in chunks)
    # No content is dropped on the hard-split path.
    assert " ".join(chunks).split() == text.split()


def test_chunk_text_respects_budget_when_tokenizer_adds_special_tokens() -> None:
    # Regression: summing per-block counts charges one BOS per block and none of
    # the separators, so chunks used to land over budget with a real tokenizer.
    tok = SpecialTokenTokenizer()
    overhead = len(tok.encode(""))
    text = "\n\n".join(
        ["# Report", "alpha " * 12, "## Section", "beta " * 18, "gamma " * 9]
    )
    for budget in (12, 20, 40, 80):
        chunks = chunk_text(text, tok, max_tokens=budget)
        assert chunks, f"budget {budget} produced no chunks"
        for chunk in chunks:
            size = len(tok.encode(chunk)) - overhead
            assert size <= budget, f"{size} > {budget} for {chunk!r}"


def test_chunk_text_does_not_leak_special_tokens_into_output() -> None:
    # The hard-split path slices token ids, so it must drop the BOS prefix
    # first or decode would write it back into the translated text.
    tok = SpecialTokenTokenizer()
    chunks = chunk_text(" ".join(f"w{i}" for i in range(40)), tok, max_tokens=5)

    assert chunks
    assert not any("<bos>" in c for c in chunks)


# -- token_overhead / count_tokens ---------------------------------------------


def test_token_overhead_counts_the_special_prefix() -> None:
    assert token_overhead(SpecialTokenTokenizer()) == 1
    assert token_overhead(FakeTokenizer()) == 0


def test_count_tokens_excludes_the_special_prefix() -> None:
    # Net length, so summing block counts doesn't charge a BOS per block.
    assert count_tokens("one two three", SpecialTokenTokenizer()) == 3
    assert count_tokens("", SpecialTokenTokenizer()) == 0


# -- split_oversized -----------------------------------------------------------


def test_split_oversized_keeps_whole_sentences_when_they_fit() -> None:
    pieces = split_oversized("Alpha one. Beta two.", FakeTokenizer(), 3)

    assert pieces == ["Alpha one.", "Beta two."]


def test_split_oversized_handles_cjk_full_stops() -> None:
    # The app translates across 67 languages, so CJK sentence enders count too.
    pieces = split_oversized("第一文です。 第二文です。", FakeTokenizer(), 2)

    assert pieces == ["第一文です。", "第二文です。"]


# -- cached_document_chunks ----------------------------------------------------


@patch("streamlit_app.chunk_document")
@patch("streamlit_app.load_document")
@patch("streamlit_app.load_model")
def test_cached_document_chunks_composes_load_and_chunk(
    mock_load_model: MagicMock,
    mock_load_document: MagicMock,
    mock_chunk_document: MagicMock,
) -> None:
    cached = streamlit_app.cached_document_chunks
    cached.clear()
    tokenizer = MagicMock()
    mock_load_model.return_value = (MagicMock(), tokenizer)
    doc = MagicMock()
    mock_load_document.return_value = doc
    mock_chunk_document.return_value = ["chunk a", "chunk b"]

    result = cached(b"bytes", "report.pdf")

    # Pulls the tokenizer from load_model() rather than taking it as an arg, then
    # composes load_document -> chunk_document.
    assert result == ["chunk a", "chunk b"]
    mock_load_document.assert_called_once_with(b"bytes", "report.pdf")
    mock_chunk_document.assert_called_once_with(
        doc, tokenizer, streamlit_app.MAX_CHUNK_TOKENS
    )


@patch("streamlit_app.chunk_document")
@patch("streamlit_app.load_document")
@patch("streamlit_app.load_model")
def test_cached_document_chunks_forwards_custom_max_tokens(
    mock_load_model: MagicMock,
    _mock_load_document: MagicMock,
    mock_chunk_document: MagicMock,
) -> None:
    cached = streamlit_app.cached_document_chunks
    cached.clear()
    mock_load_model.return_value = (MagicMock(), MagicMock())
    mock_chunk_document.return_value = []

    cached(b"x", "a.pdf", max_tokens=1234)

    assert mock_chunk_document.call_args[0][2] == 1234


@patch("streamlit_app.chunk_text")
@patch("streamlit_app.load_document_markdown")
@patch("streamlit_app.load_model")
def test_cached_document_chunks_routes_liteparse_backend(
    mock_load_model: MagicMock,
    mock_load_markdown: MagicMock,
    mock_chunk_text: MagicMock,
) -> None:
    cached = streamlit_app.cached_document_chunks
    cached.clear()
    tokenizer = MagicMock()
    mock_load_model.return_value = (MagicMock(), tokenizer)
    mock_load_markdown.return_value = "# Doc\n\nBody."
    mock_chunk_text.return_value = ["chunk"]

    result = cached(b"bytes", "report.pdf", streamlit_app.PARSER_LITEPARSE)

    assert result == ["chunk"]
    # LiteParse takes bytes only -- it sniffs the format itself, no filename.
    mock_load_markdown.assert_called_once_with(b"bytes")
    mock_chunk_text.assert_called_once_with(
        "# Doc\n\nBody.", tokenizer, streamlit_app.MAX_CHUNK_TOKENS
    )


@patch("streamlit_app.chunk_text")
@patch("streamlit_app.load_document_markdown")
@patch("streamlit_app.chunk_document")
@patch("streamlit_app.load_document")
@patch("streamlit_app.load_model")
def test_cached_document_chunks_backend_selects_one_path_only(
    mock_load_model: MagicMock,
    mock_load_document: MagicMock,
    mock_chunk_document: MagicMock,
    mock_load_markdown: MagicMock,
    mock_chunk_text: MagicMock,
) -> None:
    cached = streamlit_app.cached_document_chunks
    cached.clear()
    mock_load_model.return_value = (MagicMock(), MagicMock())
    mock_chunk_document.return_value = []

    cached(b"bytes", "report.pdf", streamlit_app.PARSER_DOCLING)

    # The Docling path must not touch LiteParse, so an uninstalled LiteParse
    # can never break a Docling parse.
    mock_load_document.assert_called_once()
    mock_load_markdown.assert_not_called()
    mock_chunk_text.assert_not_called()


def test_cached_document_chunks_keys_on_backend() -> None:
    # backend is part of the cache key: switching parsers on the same upload
    # must re-parse rather than return the other backend's chunks.
    source = "".join(_APP_SOURCE.split())
    assert "defcached_document_chunks(file_bytes:bytes,filename:str,backend:str" in (
        source
    )


def test_document_tab_calls_cache_wrapper() -> None:
    # AppTest can't drive st.file_uploader, so guard the wiring at the source
    # level: the Document tab must go through cached_document_chunks, not call
    # load_document/chunk_document directly (which would silently bypass the
    # parse+chunk cache). Strip whitespace so line-wrapping can't break the match.
    compact = "".join(_APP_SOURCE.split())
    assert "cached_document_chunks(uploaded.getvalue(),uploaded.name,parser)" in compact


# -- translate_document --------------------------------------------------------


@patch("mlx_lm.stream_generate")
def test_translate_document_yields_cumulative_per_chunk(
    mock_stream_generate: MagicMock,
) -> None:
    mock_stream_generate.side_effect = [
        iter([_make_chunk("Bon"), _make_chunk("jour")]),
        iter([_make_chunk("Salut")]),
    ]

    results = list(
        translate_document(
            ["chunk one", "chunk two"],
            "English",
            "French",
            MagicMock(),
            MagicMock(),
        )
    )

    assert results == [
        (0, "Bon"),
        (0, "Bonjour"),
        (1, "Bonjour\n\nSalut"),
    ]


@patch("mlx_lm.stream_generate")
def test_translate_document_handles_empty_chunk_list(
    mock_stream_generate: MagicMock,
) -> None:
    results = list(
        translate_document([], "English", "French", MagicMock(), MagicMock())
    )

    assert results == []
    mock_stream_generate.assert_not_called()


@patch("mlx_lm.stream_generate")
def test_translate_document_tokenizes_each_chunk(
    mock_stream_generate: MagicMock,
) -> None:
    mock_stream_generate.side_effect = [
        iter([_make_chunk("a")]),
        iter([_make_chunk("b")]),
    ]
    mock_tokenizer = MagicMock()

    list(
        translate_document(
            ["one", "two"], "English", "French", MagicMock(), mock_tokenizer
        )
    )

    assert mock_tokenizer.apply_chat_template.call_count == 2


@patch("mlx_lm.stream_generate")
def test_translate_document_skips_chunk_over_token_limit(
    mock_stream_generate: MagicMock,
) -> None:
    mock_tokenizer = MagicMock()
    mock_tokenizer.apply_chat_template.return_value = list(range(9000))

    results = list(
        translate_document(
            ["a very long chunk"],
            "English",
            "French",
            MagicMock(),
            mock_tokenizer,
        )
    )

    assert len(results) == 1
    idx, text = results[0]
    assert idx == 0
    assert "skipped" in text.lower()
    mock_stream_generate.assert_not_called()


@patch("mlx_lm.stream_generate")
def test_translate_document_omits_blank_chunk_output(
    mock_stream_generate: MagicMock,
) -> None:
    mock_stream_generate.side_effect = [
        iter([]),
        iter([_make_chunk("Salut")]),
    ]

    results = list(
        translate_document(
            ["one", "two"], "English", "French", MagicMock(), MagicMock()
        )
    )

    assert results == [(1, "Salut")]


# -- render_output -------------------------------------------------------------


def test_render_output_renders_code_with_panel_height() -> None:
    # render_output is the single sink for streamed output across both tabs; it
    # must use st.code (non-widget, replaceable mid-script without a widget-id
    # collision) with wrap_lines and the shared PANEL_HEIGHT, not st.text_area.
    placeholder = MagicMock()

    render_output(placeholder, "Bonjour")

    placeholder.code.assert_called_once_with(
        "Bonjour",
        language=None,
        wrap_lines=True,
        height=streamlit_app.PANEL_HEIGHT,
    )


def test_render_output_is_single_code_sink() -> None:
    # render_output is the single st.code sink; guard against re-inlining
    # `.code(...)` at a call site, which passes the helper unit test and the
    # height-literal guard yet defeats the dedup the refactor exists for.
    assert _APP_SOURCE.count(".code(") == 1

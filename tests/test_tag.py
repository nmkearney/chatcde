"""Tests for ``chatcde tag`` (issue #15). No network: a fake endpoint.

The fake answers each batch's JSON schema (sent as ``response_format``) with the
first allowed code of every dimension and a quote from the record's title, so
the quotes are found in the metadata. Records whose title is in ``bad_titles``
get an answer that never validates, and ``invented`` titles get quotes that are
not in the text.
"""

from __future__ import annotations

import json
import shutil
from pathlib import Path
from typing import Any

import duckdb
import httpx
import pytest
import yaml
from pydantic import ValidationError
from typer.testing import CliRunner

from chatcde.cli import app
from chatcde.config import Config, load_config
from chatcde.schemas import Dimension, Provenance, Tag, TextSource
from chatcde.store.endpoint import EndpointClient
from chatcde.tag import tables
from chatcde.tag.answer import OTHER, batch_model, codes_for
from chatcde.tag.derive import derive, derived_provenance, none_tags, publish
from chatcde.tag.extract import RecordText
from chatcde.tag.llm import load_prompt
from chatcde.tag.prompt import split_template, system_prompt
from chatcde.tag.regions import (
    GLOBAL_FLAG,
    PARTNER_COUNTRY,
    RegionMap,
    country_lookup,
    load_countries,
)
from chatcde.tag.run import locate, scope_ids, tag_records, to_tags
from chatcde.tag.sample import draw_pilot
from chatcde.tag.vocabulary import load_vocabulary

# --- fakes ----------------------------------------------------------------------


def _first_code(schema: dict[str, Any], ref: str) -> tuple[str, bool]:
    """First enum value of an item definition, and whether it has a role field."""
    item = schema["$defs"][ref.split("/")[-1]]
    return item["properties"]["term"]["enum"][0], "role" in item["properties"]


class FakeLLM:
    """``httpx.MockTransport`` handler answering tagging requests."""

    def __init__(self) -> None:
        self.chat: list[dict[str, Any]] = []
        self.bad_titles: set[str] = set()
        self.invented: set[str] = set()

    def __call__(self, request: httpx.Request) -> httpx.Response:
        body = json.loads(request.content)
        self.chat.append(body)
        user = body["messages"][1]["content"]
        title = user.splitlines()[0].removeprefix("Title: ")
        schema = body["response_format"]["json_schema"]["schema"]
        if title in self.bad_titles:
            content = "not json"
        else:
            quote = (
                "words that are nowhere in the input"
                if title in self.invented
                else " ".join(title.split()[:6])
            )
            answer: dict[str, list[dict[str, Any]]] = {}
            for dim, prop in schema["properties"].items():
                code, has_role = _first_code(schema, prop["items"]["$ref"])
                item: dict[str, Any] = {
                    "term": code,
                    "evidence": quote,
                    "strength": "explicit",
                }
                defs = schema["$defs"][prop["items"]["$ref"].split("/")[-1]]
                if "other_label" in defs["properties"]:
                    item["other_label"] = None
                if has_role:
                    item["role"] = "studied"
                answer[dim] = [item, dict(item)]  # a duplicate, dropped by code
            content = json.dumps(answer)
        return httpx.Response(
            200,
            json={
                "choices": [{"message": {"content": content}, "finish_reason": "stop"}]
            },
        )


def make_client(fake: FakeLLM) -> EndpointClient:
    return EndpointClient(
        "https://llm.test/v1",
        "secret",
        timeout_s=5,
        max_retries=0,
        transport=httpx.MockTransport(fake),
        sleep=lambda _: None,
    )


@pytest.fixture
def db(fixture_db: Path, tmp_path: Path) -> Path:
    """A writable copy of the fixture catalogue."""
    path = tmp_path / "catalogue.duckdb"
    shutil.copy(fixture_db, path)
    return path


def make_cfg(tmp_path: Path, db: Path, **tagging: Any) -> tuple[Config, Path]:
    override = tmp_path / "override.yaml"
    override.write_text(
        yaml.safe_dump(
            {
                "data": {"catalogue": str(db)},
                "logging": {"file": None},
                "tagging": {"pilot": {"size": 6, "seed": 1, "floor": 0}, **tagging},
            }
        ),
        encoding="utf-8",
    )
    return load_config(override), override


@pytest.fixture(scope="module")
def cfg0() -> Config:
    return load_config()


@pytest.fixture(scope="module")
def vocab(cfg0: Config) -> dict[str, Any]:
    return load_vocabulary(cfg0.vocab.file)


@pytest.fixture(scope="module")
def countries(cfg0: Config) -> dict[str, Any]:
    return load_countries(cfg0.tagging.m49_file)


# --- regions --------------------------------------------------------------------


def test_region_terms(vocab: dict[str, Any], countries: dict[str, Any]):
    rm = RegionMap(countries, vocab)
    assert rm.terms("MDG") == ["Eastern Africa", "CDE-EAF", PARTNER_COUNTRY]
    assert rm.terms("ECU") == ["South America", "CDE-SAM"]
    assert rm.terms("NPL") == ["Southern Asia", PARTNER_COUNTRY]  # in no partner region
    assert rm.terms("CHE") == ["Western Europe", "CDE-EUR"]
    assert rm.terms("VNM") == ["South-eastern Asia", "CDE-MSEA"]  # by country list
    assert rm.terms("CAN") == ["Northern America"]
    assert rm.terms(GLOBAL_FLAG) == [] and rm.terms("XXX") == []
    assert len(countries) > 240


# --- schema ---------------------------------------------------------------------


def test_batch_model_offers_only_live_codes(
    cfg0: Config, vocab: dict[str, Any], countries: dict[str, Any]
):
    method = codes_for("method", vocab, countries)
    live = [t["code"] for t in vocab["method"]["terms"]]
    assert method == [*live, OTHER]
    assert "MET-futures-methods" not in method  # retired
    assert not any(c.startswith("MET-G-") for c in method)  # groups are not terms
    assert OTHER not in codes_for("sub_area", vocab, countries)
    assert {"CHE", GLOBAL_FLAG} <= set(codes_for("country", vocab, countries))
    assert codes_for("sdg", vocab, countries) == [str(n) for n in range(1, 18)]
    jus = codes_for("justice_lens", vocab, countries, exclude={"JUS-none-explicit"})
    assert "JUS-none-explicit" not in jus and "JUS-power" in jus

    s = cfg0.tagging
    model = batch_model("who_what", s.batches["who_what"], vocab, countries, s)
    ok = {
        "system": [],
        "actors": [
            {
                "term": "ACT-women",
                "evidence": "q",
                "strength": "weak",
                "other_label": None,
                "role": "studied",
            }
        ],
        "justice_lens": [],
        "sdg": [{"term": "15", "evidence": "q", "strength": "explicit"}],
        "audience_type": [],
    }
    model.model_validate(ok)
    for bad in (
        {**ok, "sdg": [{"term": "18", "evidence": "q", "strength": "explicit"}]},
        {**ok, "actors": [{**ok["actors"][0], "role": None}]},
        {
            **ok,
            "sdg": [
                {"term": str(n), "evidence": "q", "strength": "weak"}
                for n in (1, 2, 3, 4, 5, 6)
            ],
        },  # more than 5 (tagging.max_per_dimension.sdg)
        {**ok, "extra": []},
    ):
        with pytest.raises(ValidationError):
            model.model_validate(bad)


def test_country_codes_are_normalised_before_validation(
    cfg0: Config,
    vocab: dict[str, Any],
    countries: dict[str, Any],
    caplog: pytest.LogCaptureFixture,
):
    """#70: sports codes, alpha-2 codes and names map to alpha-3; others are dropped."""
    s = cfg0.tagging
    model = batch_model("how_where", s.batches["how_where"], vocab, countries, s)
    tag = {"evidence": "q", "strength": "explicit"}
    terms = ["LIT", "MOR", "np", "Switzerland", "CHE", GLOBAL_FLAG, "KOS", "DAT-x"]
    answer = model.model_validate(
        {
            "method": [],
            "data_type": [],
            "setting": [],
            "scale": [],
            "country": [{**tag, "term": t} for t in terms],
        }
    )
    got = [t.term for t in answer.country]
    assert got == ["LTU", "MAR", "NPL", "CHE", "CHE", GLOBAL_FLAG]
    assert "'KOS' is not a country" in caplog.text
    assert "'DAT-x' is not a country" in caplog.text


def test_country_lookup_never_remaps_iso_codes(countries: dict[str, Any]):
    lookup = country_lookup(countries, {"LIT": "LTU", "che": "DEU"})
    assert lookup["LIT"] == "LTU"
    assert lookup["CHE"] == "CHE"  # a valid alpha-3 code wins over an alias
    assert lookup["DE"] == "DEU"
    with pytest.raises(ValueError, match="unknown alpha-3"):
        country_lookup(countries, {"LIT": "XXX"})


# --- prompt ---------------------------------------------------------------------


def test_system_prompt_lists_the_batch(cfg0: Config, vocab: dict[str, Any]):
    s = cfg0.tagging
    template = load_prompt(cfg0.prompts.dir, s.prompt)
    head, rules = split_template(template)
    assert "{{dimensions}}" in head
    assert set(rules) == {d for dims in s.batches.values() for d in dims}

    text = system_prompt(template, s.batches["how_where"], vocab, s)
    assert "## method (at most 5 tags)" in text and "## actors" not in text
    assert "#### Participatory and transdisciplinary" in text  # group heading
    assert "- MET-case-study — Case study" in text
    assert "- other — none of the above fits" in text
    assert "{{" not in text

    strategy = system_prompt(template, s.batches["strategy"], vocab, s)
    assert "#### SL: Sustainable land systems" in strategy
    assert "#### Cross-cutting" in strategy  # additional sub-areas by impact area
    who = system_prompt(template, s.batches["who_what"], vocab, s)
    assert "JUS-procedural" in who and "JUS-none-explicit" not in who  # none_terms
    with pytest.raises(ValueError, match="no '### region' rules"):
        system_prompt(template, ["region"], vocab, s)


# --- answers to tags ------------------------------------------------------------


def _record() -> RecordText:
    return RecordText(
        "r1",
        "Title: Soil erosion in Nepal\n\nAbstract:\nWe interviewed farmers.",
        "abstract,fulltext",
        metadata="Title: Soil erosion in Nepal",
        abstract="We interviewed farmers about terrace maintenance.",
        abstract_source="abstract_openalex",
        fulltext="A household survey of 120 farms in the hills.",
    )


def test_locate_finds_the_part_a_quote_comes_from():
    rec = _record()
    assert (
        locate("interviewed farmers about terrace", rec) is TextSource.ABSTRACT_OPENALEX
    )
    assert locate("household survey of 120 farms", rec) is TextSource.FULLTEXT
    assert locate("Soil erosion in Nepal", rec) is TextSource.METADATA
    assert locate("something else entirely here", rec) is None


def test_to_tags_maps_strength_checks_quotes_and_drops_repeats(
    cfg0: Config, vocab: dict[str, Any], countries: dict[str, Any]
):
    s = cfg0.tagging
    model = batch_model("how_where", s.batches["how_where"], vocab, countries, s)
    item = {"other_label": None}
    answer = model.model_validate(
        {
            "method": [
                {
                    **item,
                    "term": "MET-household-and-other-surveys",
                    "evidence": "household survey of 120 farms",
                    "strength": "explicit",
                },
                {
                    **item,
                    "term": "MET-household-and-other-surveys",
                    "evidence": "household survey of 120 farms",
                    "strength": "weak",
                },
                {
                    **item,
                    "term": "MET-case-study",
                    "evidence": "not in the input at all",
                    "strength": "explicit",
                },
                {
                    **item,
                    "term": OTHER,
                    "evidence": "interviewed farmers about terrace",
                    "strength": "inferred",
                },  # other without a label: dropped
            ],
            "data_type": [],
            "setting": [],
            "scale": [],
            "country": [
                {
                    "term": "NPL",
                    "evidence": "Soil erosion in Nepal",
                    "strength": "explicit",
                }
            ],
        }
    )
    prov = Provenance(code_version="x", created_at="2026-11-09T00:00:00Z", model="m")
    rows, unverified = to_tags(
        answer,
        _record(),
        batch="how_where",
        dimensions=s.batches["how_where"],
        cfg=cfg0,
        provenance=prov,
        run="main",
    )
    got = {(r.dimension.value, r.term): r for r in rows}
    assert set(got) == {
        ("method", "MET-household-and-other-surveys"),
        ("method", "MET-case-study"),
        ("country", "NPL"),
    }
    assert got[("method", "MET-household-and-other-surveys")].confidence == 0.9
    assert (
        got[("method", "MET-household-and-other-surveys")].source is TextSource.FULLTEXT
    )
    capped = got[("method", "MET-case-study")]
    assert unverified == 1 and capped.confidence == s.unverified_cap
    assert capped.source is TextSource.FULLTEXT  # fallback: richest part
    assert got[("country", "NPL")].source is TextSource.METADATA


def test_metadata_only_records_count_only_explicit_tags(
    cfg0: Config, vocab: dict[str, Any], countries: dict[str, Any]
):
    s = cfg0.tagging
    model = batch_model("how_where", s.batches["how_where"], vocab, countries, s)
    q = {"evidence": "Soil erosion in Nepal", "other_label": None}
    answer = model.model_validate(
        {
            "method": [{**q, "term": "MET-case-study", "strength": "inferred"}],
            "data_type": [],
            "setting": [{**q, "term": "SET-mountains", "strength": "explicit"}],
            "scale": [{**q, "term": "SCA-national", "strength": "inferred"}],
            "country": [{"evidence": "Nepal", "term": "NPL", "strength": "inferred"}],
        }
    )
    title_only = RecordText(
        "r2",
        "Title: Soil erosion in Nepal",
        "metadata",
        metadata="Title: Soil erosion in Nepal",
    )
    prov = Provenance(code_version="x", created_at="2026-11-09T00:00:00Z", model="m")
    rows, _ = to_tags(
        answer,
        title_only,
        batch="how_where",
        dimensions=s.batches["how_where"],
        cfg=cfg0,
        provenance=prov,
        run="main",
    )
    conf = {r.term: r.confidence for r in rows}
    assert conf == {
        "MET-case-study": s.metadata_only_cap,
        "SET-mountains": 0.9,
        "SCA-national": s.metadata_only_cap,
        "NPL": 0.6,  # country is in tagging.metadata_inferable
    }


# --- runs -----------------------------------------------------------------------


def _ids(con: duckdb.DuckDBPyConnection, n: int) -> list[str]:
    return [
        r[0]
        for r in con.execute(
            "SELECT record_id FROM records ORDER BY record_id LIMIT ?", [n]
        ).fetchall()
    ]


def test_tag_records_resumes_and_retries(db: Path, tmp_path: Path):
    cfg, _ = make_cfg(tmp_path, db)
    con = duckdb.connect(str(db))
    ids = _ids(con, 3)
    title = con.execute(
        "SELECT title FROM records WHERE record_id = ?", [ids[0]]
    ).fetchone()[0]
    fake = FakeLLM()
    fake.bad_titles.add(title)
    client = make_client(fake)

    s = tag_records(con, cfg, client, scope="ids", ids=ids)
    n_batches = len(cfg.tagging.batches)
    assert s.jobs == 3 * n_batches and s.failed == n_batches and s.done == 2 * n_batches
    assert len(fake.chat) == 2 * n_batches + 2 * n_batches  # bad answers: 2 attempts
    rows = con.execute("SELECT * FROM tag_runs").fetchall()
    assert rows and s.tags_by_dimension["method"] == 2  # duplicate dropped, 2 records
    cols = [c[0] for c in con.description]
    for row in rows:
        Tag.model_validate(
            {k: v for k, v in zip(cols, row, strict=True) if k in Tag.model_fields}
        )
    assert s.unverified_share == 0  # quotes from the title are found
    assert (
        s.unused_terms["method"]
        == len(
            codes_for(
                "method",
                load_vocabulary(cfg.vocab.file),
                load_countries(cfg.tagging.m49_file),
            )
        )
        - 2
    )  # 'other' is not counted; one code used

    fake.bad_titles.clear()
    again = tag_records(con, cfg, client, scope="ids", ids=ids)
    assert again.skipped == 2 * n_batches and again.done == n_batches  # error retried
    calls = len(fake.chat)
    third = tag_records(con, cfg, client, scope="ids", ids=ids)
    assert third.skipped == 3 * n_batches and len(fake.chat) == calls
    forced = tag_records(
        con, cfg, client, scope="ids", ids=ids[:1], batches=["strategy"], force=True
    )
    assert forced.done == 1 and forced.batches == ["strategy"]
    states = con.execute(
        "SELECT count(*), count(DISTINCT record_id) FROM tag_state WHERE status = 'ok'"
    ).fetchone()
    assert states == (3 * n_batches, 3)
    con.close()


def test_unverified_quotes_are_capped(db: Path, tmp_path: Path):
    cfg, _ = make_cfg(tmp_path, db)
    con = duckdb.connect(str(db))
    ids = _ids(con, 1)
    title = con.execute(
        "SELECT title FROM records WHERE record_id = ?", [ids[0]]
    ).fetchone()[0]
    fake = FakeLLM()
    fake.invented.add(title)
    s = tag_records(
        con, cfg, make_client(fake), scope="ids", ids=ids, batches=["strategy"]
    )
    assert s.unverified_share == 1
    top = con.execute("SELECT max(confidence) FROM tag_runs").fetchone()[0]
    assert top == cfg.tagging.unverified_cap
    con.close()


def test_scope_and_bad_batch(db: Path, tmp_path: Path):
    cfg, _ = make_cfg(tmp_path, db)
    con = duckdb.connect(str(db))
    assert (
        len(scope_ids(con, "all"))
        == con.execute("SELECT count(*) FROM records").fetchone()[0]
    )
    with pytest.raises(ValueError, match="not in the catalogue"):
        scope_ids(con, "ids", ["nope"])
    with pytest.raises(RuntimeError, match="no pilot"):
        scope_ids(con, "pilot")
    with pytest.raises(ValueError, match="unknown batch"):
        tag_records(con, cfg, make_client(FakeLLM()), scope="all", batches=["nope"])
    con.close()


def test_pilot_excludes_the_vocabulary_sample(db: Path, tmp_path: Path):
    cfg, _ = make_cfg(tmp_path, db)
    con = duckdb.connect(str(db))
    tables.ensure(con, "vocab_sample")
    excluded = _ids(con, 10)
    con.executemany(
        "INSERT INTO vocab_sample VALUES "
        "(?, 'u|d|l', 'u', 'd', 'l', false, 13, 250, 3, now(), 'x')",
        [[i] for i in excluded],
    )
    s = draw_pilot(con, cfg)
    picked = {r[0] for r in con.execute("SELECT record_id FROM tag_pilot").fetchall()}
    assert s.sampled == len(picked) == 6 and not picked & set(excluded)
    total = con.execute("SELECT count(*) FROM records").fetchone()[0]
    assert s.eligible == total - 10  # metadata-only records are eligible too
    assert draw_pilot(con, cfg).reused
    assert set(scope_ids(con, "pilot")) == picked
    con.close()


# --- publish --------------------------------------------------------------------


def _tag(rid: str, dim: str, term: str, conf: float) -> Tag:
    return Tag(
        record_id=rid,
        dimension=Dimension(dim),
        term=term,
        confidence=conf,
        evidence="q",
        source=TextSource.METADATA,
        provenance=Provenance(code_version="x", created_at="2026-11-09T00:00:00Z"),
    )


def test_derive_region_and_impact_area(
    vocab: dict[str, Any], countries: dict[str, Any]
):
    asa = {t["impact_area"]: t["code"] for t in vocab["additional_sub_area"]["terms"]}
    tags = [
        _tag("r1", "country", "MDG", 0.9),
        _tag("r1", "country", "KEN", 0.6),
        _tag("r1", "sub_area", "SL-a", 0.6),
        _tag("r1", "sub_area", "SL-d", 0.9),
        _tag("r1", "additional_sub_area", asa["SG"], 0.6),
        _tag("r1", "additional_sub_area", asa["cross_cutting"], 0.9),
        _tag("r2", "country", GLOBAL_FLAG, 0.9),
    ]
    got = {
        (t.record_id, t.dimension.value, t.term): t
        for t in derive(tags, vocab, RegionMap(countries, vocab))
    }
    assert set(got) == {
        ("r1", "region", "Eastern Africa"),
        ("r1", "region", "CDE-EAF"),
        ("r1", "region", PARTNER_COUNTRY),
        ("r1", "impact_area", "SL"),
        ("r1", "impact_area", "SG"),
    }
    assert got[("r1", "region", "CDE-EAF")].confidence == 0.9  # highest origin
    assert got[("r1", "impact_area", "SL")].confidence == 0.9
    assert all(
        t.evidence is None and t.provenance.model == "derived" for t in got.values()
    )


def test_none_tags_fill_records_read_without_a_counted_tag(vocab: dict[str, Any]):
    tags = [
        _tag("r1", "justice_lens", "JUS-power", 0.9),  # counted lens: no "none"
        _tag("r2", "justice_lens", "JUS-gender", 0.3),  # weak only: "none"
        _tag("r3", "sdg", "1", 0.9),
    ]
    tags[2] = tags[2].model_copy(update={"source": TextSource.ABSTRACT_OPENALEX})
    read = {
        "justice_lens": {
            "r1": "fulltext",
            "r2": "abstract,fulltext",
            "r3": "abstract",
            "r4": "metadata",  # title only: absence says nothing
        }
    }
    got = none_tags(
        tags,
        read,
        {"justice_lens": "JUS-none-explicit"},
        0.6,
        derived_provenance(vocab),
    )
    assert [(t.record_id, t.term, t.source) for t in got] == [
        ("r2", "JUS-none-explicit", TextSource.FULLTEXT),
        ("r3", "JUS-none-explicit", TextSource.ABSTRACT_OPENALEX),
    ]
    assert all(t.confidence == 0.6 and t.evidence is None for t in got)


def test_publish_replaces_tags(db: Path, tmp_path: Path):
    cfg, _ = make_cfg(tmp_path, db)
    con = duckdb.connect(str(db))
    with pytest.raises(RuntimeError, match="no tags"):
        publish(con, cfg)
    ids = _ids(con, 2)
    tag_records(con, cfg, make_client(FakeLLM()), scope="ids", ids=ids)
    s = publish(con, cfg)
    assert s.records_tagged == 2 and s.llm_tags > 0
    rows = con.execute(
        "SELECT count(*), count(DISTINCT record_id) FROM tags"
    ).fetchone()
    derived = s.region_tags + s.impact_area_tags + s.none_tags
    assert rows == (s.llm_tags + derived, 2)  # fixtures gone
    assert s.impact_area_tags == 2  # first sub_area code (JE-a) -> JE, per record
    units = con.execute(
        "SELECT count(*) FROM records WHERE list_contains(?, record_id) "
        "AND len(cde_units) > 0",
        [ids],
    ).fetchone()[0]
    assert s.records_with_unit <= units  # only the tagged records are counted
    con.close()


# --- CLI ------------------------------------------------------------------------


def test_cli_tag(db: Path, tmp_path: Path, monkeypatch: pytest.MonkeyPatch):
    from chatcde.store import endpoint

    fake = FakeLLM()
    real_init = endpoint.EndpointClient.__init__

    def init_with_fake(self, *args, **kwargs):  # type: ignore[no-untyped-def]
        kwargs["transport"] = httpx.MockTransport(fake)
        real_init(self, *args, **kwargs)

    monkeypatch.setattr(endpoint.EndpointClient, "__init__", init_with_fake)
    _, override = make_cfg(tmp_path, db)
    runner = CliRunner()
    base = ["--config", str(override), "tag"]
    assert runner.invoke(app, base).exit_code == 2  # no scope chosen
    result = runner.invoke(app, [*base, "--pilot", "--batch", "strategy"])
    assert result.exit_code == 0, result.output
    for title in ("tag: pilot draw", "tag: run main (pilot)", "published run main"):
        assert title in result.output
    alt = runner.invoke(app, [*base, "--pilot", "--alternative", "--batch", "strategy"])
    assert alt.exit_code == 0, alt.output
    assert "tag: run alt (pilot)" in alt.output and "published" not in alt.output
    con = duckdb.connect(str(db), read_only=True)
    runs = dict(
        con.execute("SELECT run, count(*) FROM tag_runs GROUP BY run").fetchall()
    )
    assert set(runs) == {"main", "alt"}
    con.close()


# --- review workbook ------------------------------------------------------------


def test_review_sheet(db: Path, tmp_path: Path):
    from openpyxl import load_workbook

    from chatcde.tag.review import export_review

    cfg, _ = make_cfg(
        tmp_path,
        db,
        review={
            "records": {"fulltext": 2, "abstract": 2, "metadata": 2},
            "seed": 1,
            "dir": str(tmp_path / "reference"),
            "text_chars": 500,
        },
    )
    con = duckdb.connect(str(db))
    with pytest.raises(RuntimeError, match="no pilot records tagged"):
        export_review(con, cfg)
    draw_pilot(con, cfg)
    tag_records(con, cfg, make_client(FakeLLM()), scope="pilot")
    path, n_records, n_tags = export_review(con, cfg)
    assert path == tmp_path / "reference" / "review_main.xlsx"
    in_run = con.execute(
        "SELECT count(*) FROM tag_runs WHERE run = 'main' AND record_id IN "
        "(SELECT record_id FROM tag_pilot)"
    ).fetchone()[0]
    assert 0 < n_records <= 6 and 0 < n_tags <= in_run
    wb = load_workbook(path)
    assert wb.sheetnames == ["README", "records", "tags", "missing", "codes"]
    tags = list(wb["tags"].iter_rows(values_only=True))
    assert (
        tags[0][:3] == ("decision", "correct_term", "note") and len(tags) == n_tags + 1
    )
    assert wb["tags"].data_validations.dataValidation  # decision dropdown
    with pytest.raises(FileExistsError):
        export_review(con, cfg)
    assert export_review(con, cfg, force=True)[0] == path

    # Re-review: judge the first tag, drop it from the run, add a new one.
    wb = load_workbook(path)
    ws = wb["tags"]
    header = [c.value for c in ws[1]]
    first = {h: c.value for h, c in zip(header, ws[2], strict=True)}
    ws.cell(row=2, column=1).value = "wrong"
    wb["missing"].append([first["record_no"], "sdg", "13", None, None])
    wb.save(path)
    con.execute(
        "UPDATE tag_runs SET term = 'MOVED' WHERE run = 'main' AND record_id = ? "
        "AND dimension = ? AND term = ?",
        [first["record_id"], first["dimension"], first["term"]],
    )
    again = tmp_path / "again.xlsx"
    _, n2, t2 = export_review(con, cfg, out=again, carry_from=path)
    assert n2 == n_records and t2 == n_tags
    wb2 = load_workbook(again)
    assert "dropped" in wb2.sheetnames
    dropped = list(wb2["dropped"].iter_rows(min_row=2, values_only=True))
    assert len(dropped) == 1 and dropped[0][0] == "wrong"
    rows = list(wb2["tags"].iter_rows(values_only=True))
    change = rows[0].index("change")
    assert sorted({r[change] for r in rows[1:]}) == ["new", "same"]
    assert sum(r[change] == "new" for r in rows[1:]) == 1
    # A decision on the new tag in a further workbook is carried with also_from.
    new_row = next(i for i, r in enumerate(rows) if r[change] == "new")
    wb2["tags"].cell(row=new_row + 1, column=1).value = "ok"
    judged = tmp_path / "judged.xlsx"
    wb2.save(judged)
    third = tmp_path / "third.xlsx"
    export_review(con, cfg, out=third, carry_from=path, also_from=[judged])
    rows3 = list(load_workbook(third)["tags"].iter_rows(values_only=True))
    assert rows3[new_row][0] == "ok" and rows3[new_row][change] == "same"
    missing = list(wb2["missing"].iter_rows(min_row=2, max_row=2, values_only=True))
    assert missing[0][:3] == (first["record_no"], "sdg", "13") and missing[0][-1] in (
        "yes",
        "no",
    )
    con.close()


def test_recall_sheet(db: Path, tmp_path: Path):
    from openpyxl import load_workbook

    from chatcde.tag.recall import export_recall
    from chatcde.tag.review import export_review

    cfg, _ = make_cfg(
        tmp_path,
        db,
        review={
            "records": {"fulltext": 2, "abstract": 2, "metadata": 2},
            "seed": 1,
            "dir": str(tmp_path / "reference"),
            "text_chars": 500,
        },
    )
    con = duckdb.connect(str(db))
    draw_pilot(con, cfg)
    tag_records(con, cfg, make_client(FakeLLM()), scope="pilot")
    review, _, _ = export_review(con, cfg)
    with pytest.raises(RuntimeError, match="no tags"):
        export_recall(con, cfg, review=review)
    # The second run: a copy of main, with one extra counted tag on a reviewed record.
    for table in ("tag_runs", "tag_state"):
        cols = [r[0] for r in con.execute(f"DESCRIBE {table}").fetchall()]
        sel = ", ".join("'alt'" if c == "run" else c for c in cols)
        con.execute(f"INSERT INTO {table} SELECT {sel} FROM {table} WHERE run = 'main'")
    rid = load_workbook(review)["records"]["B2"].value
    con.execute(
        "INSERT INTO tag_runs SELECT * REPLACE ('SL-b' AS term, 0.9 AS confidence) "
        "FROM tag_runs WHERE run = 'alt' AND record_id = ? AND dimension = 'sub_area' "
        "LIMIT 1",
        [rid],
    )
    path, n, per_dim = export_recall(con, cfg, review=review)
    assert path == tmp_path / "reference" / "recall_alt.xlsx"
    assert n == 1 and per_dim == {"sub_area": 1}
    wb = load_workbook(path)
    assert wb.sheetnames == ["README", "candidates", "agreement", "records"]
    cand = list(wb["candidates"].iter_rows(min_row=2, values_only=True))
    assert cand[0][4:6] == ("sub_area", "SL-b")
    agree = {r[0]: r for r in wb["agreement"].iter_rows(min_row=2, values_only=True)}
    assert agree["sub_area"][-1] < 1 and agree["method"][-1] == 1
    with pytest.raises(FileExistsError):
        export_recall(con, cfg, review=review)
    con.close()


def test_alternative_model_uses_its_own_request_settings(db: Path, tmp_path: Path):
    cfg, _ = make_cfg(tmp_path, db)
    con = duckdb.connect(str(db))
    ids = _ids(con, 1)
    fake = FakeLLM()
    tag_records(con, cfg, make_client(fake), scope="ids", ids=ids, batches=["strategy"])
    tag_records(
        con,
        cfg,
        make_client(fake),
        scope="ids",
        ids=ids,
        batches=["strategy"],
        alternative=True,
    )
    main, alt = fake.chat
    assert main["model"] == cfg.models.tagging
    assert main["chat_template_kwargs"] == {"enable_thinking": False}
    assert alt["model"] == cfg.model_alternatives.tagging == "gpt-oss-120b"
    assert alt["max_tokens"] == 8192 and alt["reasoning_effort"] == "low"
    assert "chat_template_kwargs" not in alt
    con.close()

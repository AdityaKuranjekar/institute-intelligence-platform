"""Comprehensive acceptance test suite for Agent A (`technical/datagen/`)."""

from __future__ import annotations

import datetime
import hashlib
import json
import shutil
import tempfile
import time
from pathlib import Path
from typing import Any

import jsonschema
import numpy as np
import pandas as pd
import psycopg2
import psycopg2.extras
import pyarrow as pa
import pyarrow.parquet as pq
import pytest
import yaml

from datagen.generator.institutes import COUNSELLOR_NAMES
from datagen.generator.pipeline import run_datagen_pipeline
from datagen.generator.synthetic_names import (
    FEMALE_FIRST_NAMES,
    GUARDIAN_FIRST_NAMES,
    MALE_FIRST_NAMES,
    SYNTHETIC_HEADER,
    SYNTHETIC_SURNAMES,
)
from datagen.generator.utils import (
    CONFIG_DIR,
    CONTRACTS_DIR,
    SCENARIOS_DIR,
    load_and_validate_config,
    load_json,
    load_yaml,
)
from datagen.messy.reference_parse import (
    parse_messy_file,
    strict_pandas_read_is_flagged,
)

TECH_ROOT = Path(__file__).resolve().parents[2]
DATA_DIR = TECH_ROOT / "data"


@pytest.fixture(scope="module")
def full_data_dir() -> Path:
    """Ensure `data/` has been generated with `full` preset and `seed=42`."""
    clean_students = DATA_DIR / "clean" / "students.parquet"
    cal_file = DATA_DIR / "truth" / "calibration_samples.json"
    need_run = True
    if clean_students.exists() and cal_file.exists():
        meta = load_json(cal_file)
        if meta.get("preset") == "full" and meta.get("seed") == 42:
            need_run = False
    if need_run:
        run_datagen_pipeline(seed=42, preset="full", out_dir=DATA_DIR)
    return DATA_DIR


def _sha256_file(path: Path) -> str:
    h = hashlib.sha256()
    with open(path, "rb") as f:
        for chunk in iter(lambda: f.read(65536), b""):
            h.update(chunk)
    return h.hexdigest()


# ---------------------------------------------------------------------------
# 1. Schema + Live Postgres 16 Load + PK/FK + Enum Validation
# ---------------------------------------------------------------------------
def test_01_schema_contracts_and_postgres_load(full_data_dir: Path) -> None:
    """Validate datasets.yaml schema, sort order, enums, PK/FKs, and load into live PostgreSQL 16."""
    datasets_doc = load_yaml(CONTRACTS_DIR / "datasets.yaml")
    enums_doc = load_yaml(CONTRACTS_DIR / "enums.yaml")["enums"]

    # Also validate generator_config.yaml and all 6 scenario files against generator_config.schema.json
    cfg_schema = load_json(CONFIG_DIR / "generator_config.schema.json")
    base_cfg = load_yaml(CONFIG_DIR / "generator_config.yaml")
    jsonschema.validate(instance=base_cfg, schema=cfg_schema)
    for sc_path in sorted(SCENARIOS_DIR.glob("*.yaml")):
        merged_cfg = load_and_validate_config(scenario_path=sc_path)
        jsonschema.validate(instance=merged_cfg, schema=cfg_schema)

    clean_dfs: dict[str, pd.DataFrame] = {}

    # Check every clean & truth parquet file against datasets.yaml
    for section_key, sub_dir in [("clean_tables", "clean"), ("truth_tables", "truth")]:
        for tname, spec in datasets_doc[section_key].items():
            p_path = full_data_dir / sub_dir / f"{tname}.parquet"
            assert p_path.exists(), f"Missing Parquet file: {p_path}"
            table = pq.read_table(p_path)
            df = table.to_pandas()
            if section_key == "clean_tables":
                clean_dfs[tname] = df

            expected_cols = [c["name"] for c in spec["columns"]]
            assert list(table.column_names) == expected_cols, (
                f"{tname}: column mismatch {table.column_names} vs {expected_cols}"
            )

            # Check nullability and allowed values
            for c_spec in spec["columns"]:
                cname = c_spec["name"]
                nullable = bool(c_spec["nullable"])
                col_arr = table.column(cname)
                if not nullable:
                    assert col_arr.null_count == 0, f"{tname}.{cname} is non-nullable but has {col_arr.null_count} nulls"
                if "allowed_values" in c_spec:
                    allowed = set(c_spec["allowed_values"])
                    non_null_vals = set(df[cname].dropna().unique())
                    assert non_null_vals.issubset(allowed), (
                        f"{tname}.{cname} has values {non_null_vals - allowed} outside {allowed}"
                    )

            # Check sort_by order
            sort_keys = spec["sort_by"]
            if len(df) > 1:
                df_resorted = df.sort_values(by=sort_keys, kind="mergesort").reset_index(drop=True)
                assert df[sort_keys].equals(df_resorted[sort_keys]), f"{tname} is not sorted by {sort_keys}"

    # Check enum values in clean tables against contracts/enums.yaml
    enum_col_checks = [
        ("institutes", "city_tier", "city_tier"),
        ("institutes", "exam_focus", "institute_exam_focus"),
        ("institutes", "plan", "institute_plan"),
        ("batches", "class_level", "class_level"),
        ("batches", "exam", "exam"),
        ("students", "gender", "gender"),
        ("students", "status", "student_status"),
        ("students", "fee_plan", "fee_plan"),
        ("guardians", "relation", "guardian_relation"),
        ("guardians", "lang_pref", "lang"),
        ("consents", "purpose", "consent_purpose"),
        ("consents", "verification_method", "verification_method"),
        ("questions", "q_type", "q_type"),
        ("question_topics", "tagged_by", "tagger_source"),
        ("tests", "source", "test_source"),
        ("responses", "status", "response_status"),
        ("attendance", "source", "attendance_source"),
    ]
    for tname, cname, enum_key in enum_col_checks:
        allowed_set = set(enums_doc[enum_key]["values"])
        actual_set = set(clean_dfs[tname][cname].dropna().unique())
        assert actual_set.issubset(allowed_set), (
            f"{tname}.{cname} has invalid enum values: {actual_set - allowed_set}"
        )

    # Check primary keys & foreign keys in memory
    assert clean_dfs["institutes"]["id"].is_unique
    assert clean_dfs["batches"]["id"].is_unique
    assert clean_dfs["students"]["id"].is_unique
    assert clean_dfs["questions"]["id"].is_unique
    assert clean_dfs["tests"]["id"].is_unique

    inst_set = set(clean_dfs["institutes"]["id"])
    batch_set = set(clean_dfs["batches"]["id"])
    stud_set = set(clean_dfs["students"]["id"])
    q_set = set(clean_dfs["questions"]["id"])
    test_set = set(clean_dfs["tests"]["id"])

    assert set(clean_dfs["batches"]["institute_id"]).issubset(inst_set)
    assert set(clean_dfs["students"]["institute_id"]).issubset(inst_set)
    assert set(clean_dfs["students"]["batch_id"]).issubset(batch_set)
    assert set(clean_dfs["guardians"]["student_id"]).issubset(stud_set)
    assert set(clean_dfs["consents"]["student_id"]).issubset(stud_set)
    assert set(clean_dfs["question_topics"]["question_id"]).issubset(q_set)
    assert set(clean_dfs["test_questions"]["test_id"]).issubset(test_set)
    assert set(clean_dfs["test_questions"]["question_id"]).issubset(q_set)
    assert set(clean_dfs["responses"]["test_id"]).issubset(test_set)
    assert set(clean_dfs["responses"]["student_id"]).issubset(stud_set)
    assert set(clean_dfs["responses"]["question_id"]).issubset(q_set)
    assert set(clean_dfs["test_totals"]["test_id"]).issubset(test_set)
    assert set(clean_dfs["test_totals"]["student_id"]).issubset(stud_set)
    assert set(clean_dfs["attendance"]["student_id"]).issubset(stud_set)
    assert set(clean_dfs["fees"]["student_id"]).issubset(stud_set)
    assert set(clean_dfs["engagement"]["student_id"]).issubset(stud_set)

    # Load a `tiny` dataset into live PostgreSQL 16 (via pgserver) with `contracts/schema.sql` applied
    import pgserver

    tmp_pg_dir = tempfile.mkdtemp(prefix="datamoat_datagen_pg_")
    tiny_out_dir = Path(tempfile.mkdtemp(prefix="datamoat_tiny_pg_"))
    db = pgserver.get_server(tmp_pg_dir)
    try:
        run_datagen_pipeline(seed=42, preset="tiny", out_dir=tiny_out_dir, include_messy=False, include_omr=False)
        conn = psycopg2.connect(db.get_uri())
        conn.autocommit = False
        cur = conn.cursor()
        try:
            sql_text = (CONTRACTS_DIR / "schema.sql").read_text(encoding="utf-8")
            cur.execute(sql_text)

            # Seed global reference tables required by FKs: topics, marking_schemes, model_registry
            topics_doc = load_yaml(CONTRACTS_DIR / "topics.yaml")
            for t in topics_doc["topics"]:
                cur.execute(
                    """
                    INSERT INTO topics (id, exam, subject, chapter, topic, name_en, name_hi, name_hi_reviewed, parent_id, class_level, syllabus_year, verified)
                    VALUES (%s, %s, %s, %s, %s, %s, %s, %s, %s, %s, %s, %s)
                    ON CONFLICT (id) DO NOTHING;
                    """,
                    (
                        t["id"],
                        t["exam"],
                        t["subject"],
                        t["chapter"],
                        t["topic"],
                        t["name_en"],
                        t["name_hi"],
                        bool(t.get("name_hi_reviewed", False)),
                        t.get("parent_id"),
                        t["class_level"],
                        int(t["syllabus_year"]),
                        bool(t.get("verified", False)),
                    ),
                )

            schemes_doc = load_yaml(CONTRACTS_DIR / "marking_schemes.yaml")["schemes"]
            for s_id, s_val in schemes_doc.items():
                cur.execute(
                    """
                    INSERT INTO marking_schemes (id, name, correct, wrong, blank, partial_rule, dropped_rule)
                    VALUES (%s, %s, %s, %s, %s, %s, %s)
                    ON CONFLICT (id) DO NOTHING;
                    """,
                    (
                        s_id,
                        s_val["name"],
                        float(s_val["correct"]),
                        float(s_val["wrong"]),
                        float(s_val["blank"]),
                        s_val["partial_rule"],
                        s_val["dropped_rule"],
                    ),
                )

            cur.execute(
                """
                INSERT INTO model_registry (version, trained_at, data_version, metrics)
                VALUES ('v1.0.0', '2026-10-15T18:00:00+05:30', 'seed42', '{}'::jsonb);
                """
            )

            # Load clean tables in FK order
            load_order = [
                "institutes",
                "batches",
                "students",
                "guardians",
                "consents",
                "questions",
                "question_topics",
                "item_params",
                "tests",
                "test_questions",
                "answer_keys",
                "test_totals",
                "attendance",
                "fees",
                "engagement",
                "responses",
            ]
            for tname in load_order:
                t_df = pd.read_parquet(tiny_out_dir / "clean" / f"{tname}.parquet")
                if tname == "responses":
                    # Sample 2,000 responses to verify FK/CHECK constraints quickly
                    t_df = t_df.head(2000)
                elif tname == "attendance":
                    t_df = t_df.head(2000)

                if tname == "item_params":
                    # Map datasets.yaml columns to schema.sql columns (see CCR-008)
                    rows_to_insert = []
                    for _, r in t_df.iterrows():
                        fit_flag = "suspect_wrong_key" if r["suspected_wrong_key"] else ("too_few_responses" if r["n_responses"] < 30 else "ok")
                        rows_to_insert.append(
                            (
                                r["question_id"],
                                None if pd.isna(r["institute_id"]) else r["institute_id"],
                                "v1.0.0",
                                float(r["a"]),
                                float(r["b"]),
                                float(r["c"]),
                                0.12,
                                int(r["n_responses"]),
                                fit_flag,
                            )
                        )
                    psycopg2.extras.execute_values(
                        cur,
                        """
                        INSERT INTO item_params
                        (question_id, institute_id, model_version, a, b, g, se_b, n_responses, fit_flag)
                        VALUES %s;
                        """,
                        rows_to_insert,
                    )
                else:
                    cols = list(t_df.columns)
                    records = []
                    for row_tuple in t_df.itertuples(index=False, name=None):
                        conv_row = []
                        for val in row_tuple:
                            if isinstance(val, np.ndarray):
                                conv_row.append(val.tolist())
                            elif isinstance(val, (np.integer,)):
                                conv_row.append(int(val))
                            elif isinstance(val, (np.floating,)):
                                conv_row.append(None if np.isnan(val) else float(val))
                            elif isinstance(val, (np.bool_,)):
                                conv_row.append(bool(val))
                            elif pd.isna(val):
                                conv_row.append(None)
                            elif isinstance(val, pd.Timestamp):
                                conv_row.append(val.to_pydatetime())
                            else:
                                conv_row.append(val)
                        records.append(tuple(conv_row))
                    col_list_sql = ", ".join(cols)
                    psycopg2.extras.execute_values(
                        cur,
                        f"INSERT INTO {tname} ({col_list_sql}) VALUES %s;",
                        records,
                        page_size=500,
                    )

            conn.commit()
        finally:
            cur.close()
            conn.close()
    finally:
        try:
            db.cleanup()
        except Exception:
            pass
        shutil.rmtree(tmp_pg_dir, ignore_errors=True)
        shutil.rmtree(tiny_out_dir, ignore_errors=True)


# ---------------------------------------------------------------------------
# 2. Determinism (seed 42 twice == byte-identical; seed 43 differs)
# ---------------------------------------------------------------------------
def test_02_determinism_across_seeds() -> None:
    """Two runs with seed=42 produce byte-identical SHA-256 across all outputs; seed=43 differs."""
    dir_a = Path(tempfile.mkdtemp(prefix="datamoat_det_42a_"))
    dir_b = Path(tempfile.mkdtemp(prefix="datamoat_det_42b_"))
    dir_c = Path(tempfile.mkdtemp(prefix="datamoat_det_43_"))
    try:
        run_datagen_pipeline(seed=42, preset="tiny", out_dir=dir_a)
        run_datagen_pipeline(seed=42, preset="tiny", out_dir=dir_b)
        run_datagen_pipeline(seed=43, preset="tiny", out_dir=dir_c)

        files_a = sorted(p.relative_to(dir_a) for p in dir_a.rglob("*") if p.is_file())
        files_b = sorted(p.relative_to(dir_b) for p in dir_b.rglob("*") if p.is_file())
        assert files_a == files_b
        assert len(files_a) >= 40

        for rel_p in files_a:
            # Skip comparing .xlsx zip timestamps if any, or check parquet/csv/json/png
            if rel_p.suffix in (".parquet", ".csv", ".json", ".png", ".jpg"):
                ha = _sha256_file(dir_a / rel_p)
                hb = _sha256_file(dir_b / rel_p)
                assert ha == hb, f"Non-deterministic output on {rel_p}"

        # Seed 43 must differ on clean/students.parquet and clean/responses.parquet
        assert _sha256_file(dir_a / "clean" / "students.parquet") != _sha256_file(
            dir_c / "clean" / "students.parquet"
        )
        assert _sha256_file(dir_a / "clean" / "responses.parquet") != _sha256_file(
            dir_c / "clean" / "responses.parquet"
        )
    finally:
        shutil.rmtree(dir_a, ignore_errors=True)
        shutil.rmtree(dir_b, ignore_errors=True)
        shutil.rmtree(dir_c, ignore_errors=True)


# ---------------------------------------------------------------------------
# 3. Marginals (full preset, tolerance bands)
# ---------------------------------------------------------------------------
def test_03_marginals_full_preset(full_data_dir: Path) -> None:
    """Verify all 9 required marginal distributions on the full preset."""
    students = pd.read_parquet(full_data_dir / "clean" / "students.parquet")
    batches = pd.read_parquet(full_data_dir / "clean" / "batches.parquet")
    attendance = pd.read_parquet(full_data_dir / "clean" / "attendance.parquet")
    fees = pd.read_parquet(full_data_dir / "clean" / "fees.parquet")
    responses = pd.read_parquet(full_data_dir / "clean" / "responses.parquet")
    truth_dropout = pd.read_parquet(full_data_dir / "truth" / "dropout_events.parquet")
    truth_theta = pd.read_parquet(full_data_dir / "truth" / "true_theta_topic.parquet")

    sb = students.merge(
        batches[["id", "academic_year", "class_level", "exam"]],
        left_on="batch_id",
        right_on="id",
        suffixes=("", "_b"),
    ).merge(truth_dropout, left_on="id", right_on="student_id")

    # (a) Annual dropout 12-25% per cohort-year
    for yr, grp in sb.groupby("academic_year"):
        rate = grp["dropped_out"].mean()
        assert 0.12 <= rate <= 0.25, f"Cohort {yr} dropout rate {rate:.4f} outside [0.12, 0.25]"

    # (b) Months 3-4 share >= 35% of dropouts
    drops = sb[sb["dropped_out"]].copy()
    days_to_drop = (pd.to_datetime(drops["dropout_date"]) - pd.to_datetime(drops["join_date"])).dt.days
    m34_share = ((days_to_drop >= 55) & (days_to_drop <= 125)).mean()
    assert m34_share >= 0.35, f"Months 3-4 share {m34_share:.4f} < 0.35"

    # (c) Sudden share 20-30%
    sudden_share = (drops["dropout_type"] == "sudden").mean()
    assert 0.20 <= sudden_share <= 0.30, f"Sudden dropout share {sudden_share:.4f} outside [0.20, 0.30]"

    # (d) Class mix within +-3 percentage points of 30/30/40
    cls_counts = sb["class_level"].value_counts(normalize=True)
    assert abs(cls_counts.get("class_11", 0.0) - 0.30) <= 0.03
    assert abs(cls_counts.get("class_12", 0.0) - 0.30) <= 0.03
    assert abs(cls_counts.get("dropper", 0.0) - 0.40) <= 0.03

    # (e) Attendance mean 0.78-0.86 outside dips
    att_dt = pd.to_datetime(attendance["attendance_date"])
    outside_dips = ~att_dt.dt.month.isin([10, 11, 1, 2])
    att_mean = attendance.loc[outside_dips, "present_flag"].mean()
    assert 0.78 <= att_mean <= 0.86, f"Attendance mean outside dips {att_mean:.4f} outside [0.78, 0.86]"

    # (f) Oct-Nov out-of-town dip visible (ratio 0.55-0.70)
    att_stu = attendance.merge(students[["id", "out_of_town"]], left_on="student_id", right_on="id")
    att_stu_dt = pd.to_datetime(att_stu["attendance_date"])
    oot_mask = att_stu["out_of_town"] == True
    oct_nov_mask = att_stu_dt.dt.month.isin([10, 11])
    base_oot = att_stu.loc[oot_mask & outside_dips, "present_flag"].mean()
    dip_oot = att_stu.loc[oot_mask & oct_nov_mask, "present_flag"].mean()
    dip_ratio = dip_oot / base_oot
    assert 0.55 <= dip_ratio <= 0.70, f"Oct-Nov out-of-town dip ratio {dip_ratio:.4f} outside [0.55, 0.70]"

    # (g) 15-20% late/default final instalment
    max_inst = fees.groupby("student_id")["instalment_no"].transform("max")
    final_fees = fees[fees["instalment_no"] == max_inst]
    late_or_def = (
        final_fees["paid_date"].isna()
        | (pd.to_datetime(final_fees["paid_date"]) > pd.to_datetime(final_fees["due_date"]))
    ).mean()
    assert 0.15 <= late_or_def <= 0.20, f"Final instalment late/default rate {late_or_def:.4f} outside [0.15, 0.20]"

    # (h) Blanks rate 3-15% and negatively correlated with theta (corr(blank, -theta) > 0.2)
    blank_rate = (responses["status"] == "blank").mean()
    assert 0.03 <= blank_rate <= 0.15, f"Blanks rate {blank_rate:.4f} outside [0.03, 0.15]"
    stu_blank = (
        responses.groupby("student_id")["status"]
        .apply(lambda s: (s == "blank").mean())
        .reset_index(name="blank_rate")
    )
    stu_g = truth_theta.groupby("student_id")["true_g"].first().reset_index()
    m_bt = stu_blank.merge(stu_g, on="student_id")
    corr_val = float(np.corrcoef(m_bt["blank_rate"], -m_bt["true_g"])[0, 1])
    assert corr_val > 0.20, f"corr(blank_rate, -theta) = {corr_val:.4f} <= 0.20"

    # (i) Minor fraction (< 18 at as_of 2026-10-01) >= 55% AND every student >= 16 at join_date
    as_of = pd.Timestamp("2026-10-01")
    dob_ts = pd.to_datetime(students["dob"])
    join_ts = pd.to_datetime(students["join_date"])
    age_at_join = (join_ts - dob_ts).dt.days / 365.25
    assert (age_at_join >= 15.99).all(), "Found student aged < 16 at enrolment!"
    minor_frac = ((as_of - dob_ts).dt.days / 365.25 < 18.0).mean()
    assert minor_frac >= 0.55, f"Minor fraction (<18 at as_of) {minor_frac:.4f} < 0.55"


# ---------------------------------------------------------------------------
# 4. Ground-truth calibration (empirical correct rate vs true P(correct))
# ---------------------------------------------------------------------------
def test_04_ground_truth_calibration(full_data_dir: Path) -> None:
    """Empirical correct rate by decile of true P(correct) is within 0.03 of decile mean for each institute."""
    cal_doc = load_json(full_data_dir / "truth" / "calibration_samples.json")
    for inst_id, pairs in cal_doc["calibration_samples"].items():
        arr = np.array(pairs, dtype=float)
        p_vals = arr[:, 0]
        y_vals = arr[:, 1]
        bins = np.linspace(0.0, 1.0, 11)
        checked_bins = 0
        for i in range(10):
            mask = (p_vals >= bins[i]) & (p_vals < bins[i + 1] if i < 9 else p_vals <= bins[i + 1])
            if mask.sum() >= 200:
                checked_bins += 1
                diff = abs(float(y_vals[mask].mean()) - float(p_vals[mask].mean()))
                assert diff <= 0.03, f"Institute {inst_id} decile {i} calibration diff {diff:.4f} > 0.03"
        assert checked_bins >= 5


# ---------------------------------------------------------------------------
# 5. Gradual vs sudden attendance drop in last fade weeks
# ---------------------------------------------------------------------------
def test_05_gradual_vs_sudden_attendance_fade(full_data_dir: Path) -> None:
    """For gradual dropouts, mean attendance in last fade weeks is >= 0.20 lower than baseline; for sudden, within +-0.05."""
    attendance = pd.read_parquet(full_data_dir / "clean" / "attendance.parquet")
    truth_dropout = pd.read_parquet(full_data_dir / "truth" / "dropout_events.parquet")

    att_drop = attendance.merge(truth_dropout[truth_dropout["dropped_out"]], on="student_id")
    att_drop["att_dt"] = pd.to_datetime(att_drop["attendance_date"])
    att_drop["drop_dt"] = pd.to_datetime(att_drop["dropout_date"])
    att_drop["days_before"] = (att_drop["drop_dt"] - att_drop["att_dt"]).dt.days
    att_before = att_drop[att_drop["days_before"] > 0]

    grad = att_before[att_before["dropout_type"] == "gradual"]
    grad_base = grad[grad["days_before"] > 42]["present_flag"].mean()
    grad_fade = grad[grad["days_before"] <= 35]["present_flag"].mean()
    assert (grad_base - grad_fade) >= 0.20, (
        f"Gradual fade drop {grad_base - grad_fade:.4f} < 0.20"
    )

    sud = att_before[att_before["dropout_type"] == "sudden"]
    sud_base = sud[sud["days_before"] > 42]["present_flag"].mean()
    sud_fade = sud[sud["days_before"] <= 35]["present_flag"].mean()
    assert abs(sud_base - sud_fade) <= 0.05, (
        f"Sudden pre-drop attendance change {abs(sud_base - sud_fade):.4f} > 0.05"
    )


# ---------------------------------------------------------------------------
# 6. Chronic low attenders (>= 8% with base < 0.75, dropout within +-25% relative)
# ---------------------------------------------------------------------------
def test_06_chronic_low_attenders(full_data_dir: Path) -> None:
    """>= 8% of students have base attendance < 0.75, and their dropout rate is within +-25% (relative) of overall."""
    attendance = pd.read_parquet(full_data_dir / "clean" / "attendance.parquet")
    truth_dropout = pd.read_parquet(full_data_dir / "truth" / "dropout_events.parquet")

    att_all = attendance.merge(truth_dropout[["student_id", "dropped_out", "fade_start_date"]], on="student_id")
    att_all["att_dt"] = pd.to_datetime(att_all["attendance_date"])
    att_all["fade_dt"] = pd.to_datetime(att_all["fade_start_date"])
    non_fade = att_all["fade_dt"].isna() | (att_all["att_dt"] < att_all["fade_dt"])

    base_att_df = att_all[non_fade].groupby("student_id")["present_flag"].mean().reset_index(name="base_att")
    merged = truth_dropout.merge(base_att_df, on="student_id")

    low_mask = merged["base_att"] < 0.75
    low_share = low_mask.mean()
    assert low_share >= 0.08, f"Chronic low attender share {low_share:.4f} < 0.08"

    overall_drop = merged["dropped_out"].mean()
    low_drop = merged.loc[low_mask, "dropped_out"].mean()
    rel_diff = abs(low_drop - overall_drop) / overall_drop
    assert rel_diff <= 0.25, (
        f"Chronic low attender dropout relative diff {rel_diff:.4f} > 0.25 (low={low_drop:.4f}, overall={overall_drop:.4f})"
    )


# ---------------------------------------------------------------------------
# 7. Anchor structure (>= 25% of questions shared across >= 2 institutes)
# ---------------------------------------------------------------------------
def test_07_anchor_structure(full_data_dir: Path) -> None:
    """>= 25% of questions are shared across >= 2 institutes."""
    questions = pd.read_parquet(full_data_dir / "clean" / "questions.parquet")
    test_questions = pd.read_parquet(full_data_dir / "clean" / "test_questions.parquet")

    inst_counts = test_questions.groupby("question_id")["institute_id"].nunique()
    shared_frac = (inst_counts >= 2).sum() / len(questions)
    assert shared_frac >= 0.25, f"Shared anchor question fraction {shared_frac:.4f} < 0.25"


# ---------------------------------------------------------------------------
# 8. Wrong keys (injected count == truth count; >= 80% have point-biserial < 0.05)
# ---------------------------------------------------------------------------
def test_08_wrong_keys_point_biserial(full_data_dir: Path) -> None:
    """Injected wrong keys count == truth count; >= 80% have point-biserial < 0.05 in generated responses."""
    item_params = pd.read_parquet(full_data_dir / "clean" / "item_params.parquet")
    truth_items = pd.read_parquet(full_data_dir / "truth" / "true_item_params.parquet")

    wk_truth = truth_items[truth_items["is_injected_wrong_key"] == True]
    assert len(wk_truth) >= 5

    wk_ids = set(wk_truth["question_id"])
    ip_wk = item_params[item_params["question_id"].isin(wk_ids)]
    assert len(ip_wk) == len(wk_truth)

    pb_low_share = (ip_wk["point_biserial"] < 0.05).mean()
    assert pb_low_share >= 0.80, f"Share of wrong-key items with point-biserial < 0.05 is {pb_low_share:.4f} < 0.80"


# ---------------------------------------------------------------------------
# 9. Messy files (reference_parse reproduces expected/*.json; naive pandas fails/flags)
# ---------------------------------------------------------------------------
def test_09_messy_files_and_reference_parser(full_data_dir: Path) -> None:
    """Reference parser reproduces every expected/*.json; strict naive pandas read fails or flags every file."""
    dirty_dir = full_data_dir / "dirty"
    expected_dir = dirty_dir / "expected"
    dirty_files = [p for p in sorted(dirty_dir.iterdir()) if p.is_file() and p.suffix in (".csv", ".xlsx")]
    assert len(dirty_files) >= 12, f"Expected >= 12 dirty files, found {len(dirty_files)}"

    institutes_represented = set()
    for fpath in dirty_files:
        golden_path = expected_dir / f"{fpath.name}.json"
        assert golden_path.exists(), f"Missing golden expected file for {fpath.name}"
        golden = load_json(golden_path)
        institutes_represented.add(golden["institute_id"])

        parsed = parse_messy_file(fpath)
        for k in ("ingest_type", "expected_rows_ok", "expected_rows_failed", "canonical_rows", "expected_errors"):
            assert parsed[k] == golden[k], f"Reference parser output mismatch for {fpath.name} on key {k}"

        flagged = strict_pandas_read_is_flagged(fpath, golden["ingest_type"])
        assert flagged is True, f"Naive pandas read did not flag dirty file {fpath.name}"

    assert len(institutes_represented) >= 3, "Messy files must span >= 3 institutes"


# ---------------------------------------------------------------------------
# 10. Scenarios (all 6 shift target stat in right direction; first 2 by >= 25%)
# ---------------------------------------------------------------------------
def test_10_scenarios() -> None:
    """Verify all 6 scenario configs shift their target metric in the right direction (first 2 by >= 25%)."""
    base_dir = Path(tempfile.mkdtemp(prefix="datamoat_scen_base_"))
    try:
        run_datagen_pipeline(seed=42, preset="tiny", out_dir=base_dir, include_messy=False, include_omr=False)
        base_drop = pd.read_parquet(base_dir / "truth" / "dropout_events.parquet")["dropped_out"].mean()
        base_resp_n = len(pd.read_parquet(base_dir / "clean" / "responses.parquet"))
        base_att_n = len(pd.read_parquet(base_dir / "clean" / "attendance.parquet"))
        base_sudden = (
            pd.read_parquet(base_dir / "truth" / "dropout_events.parquet")
            .query("dropped_out == True")["dropout_type"]
            .eq("sudden")
            .mean()
        )
        base_batches = pd.read_parquet(base_dir / "clean" / "batches.parquet")
        base_pub_cap = base_batches["published_capacity"].mean()
        base_tests = pd.read_parquet(base_dir / "clean" / "tests.parquet")
    finally:
        shutil.rmtree(base_dir, ignore_errors=True)

    # 1. dropout_x2: dropout rate increases by >= 25% relative
    d1 = Path(tempfile.mkdtemp(prefix="datamoat_scen_1_"))
    try:
        run_datagen_pipeline(
            seed=42, preset="tiny", out_dir=d1, scenario_path=SCENARIOS_DIR / "dropout_x2.yaml", include_messy=False, include_omr=False
        )
        drop_x2 = pd.read_parquet(d1 / "truth" / "dropout_events.parquet")["dropped_out"].mean()
        assert (drop_x2 - base_drop) / base_drop >= 0.25, f"dropout_x2 rate {drop_x2:.4f} vs base {base_drop:.4f}"
    finally:
        shutil.rmtree(d1, ignore_errors=True)

    # 2. marks_only: item-level responses decrease by >= 25% while test_totals remain populated
    d2 = Path(tempfile.mkdtemp(prefix="datamoat_scen_2_"))
    try:
        run_datagen_pipeline(
            seed=42, preset="tiny", out_dir=d2, scenario_path=SCENARIOS_DIR / "marks_only.yaml", include_messy=False, include_omr=False
        )
        resp_mo = len(pd.read_parquet(d2 / "clean" / "responses.parquet"))
        totals_mo = len(pd.read_parquet(d2 / "clean" / "test_totals.parquet"))
        assert base_resp_n > 0
        assert (base_resp_n - resp_mo) / base_resp_n >= 0.25
        assert totals_mo > 0
    finally:
        shutil.rmtree(d2, ignore_errors=True)

    # 3. no_attendance: attendance rows drop by >= 50%
    d3 = Path(tempfile.mkdtemp(prefix="datamoat_scen_3_"))
    try:
        run_datagen_pipeline(
            seed=42, preset="tiny", out_dir=d3, scenario_path=SCENARIOS_DIR / "no_attendance.yaml", include_messy=False, include_omr=False
        )
        att_na = len(pd.read_parquet(d3 / "clean" / "attendance.parquet"))
        assert att_na < base_att_n * 0.50
    finally:
        shutil.rmtree(d3, ignore_errors=True)

    # 4. sudden_heavy: sudden share increases to >= 0.55
    d4 = Path(tempfile.mkdtemp(prefix="datamoat_scen_4_"))
    try:
        run_datagen_pipeline(
            seed=42, preset="tiny", out_dir=d4, scenario_path=SCENARIOS_DIR / "sudden_heavy.yaml", include_messy=False, include_omr=False
        )
        sud_hv = (
            pd.read_parquet(d4 / "truth" / "dropout_events.parquet")
            .query("dropped_out == True")["dropout_type"]
            .eq("sudden")
            .mean()
        )
        assert sud_hv > base_sudden and sud_hv >= 0.50
    finally:
        shutil.rmtree(d4, ignore_errors=True)

    # 5. small_batches: batch capacity and students per batch shrink to ~30
    d5 = Path(tempfile.mkdtemp(prefix="datamoat_scen_5_"))
    try:
        run_datagen_pipeline(
            seed=42, preset="tiny", out_dir=d5, scenario_path=SCENARIOS_DIR / "small_batches.yaml", include_messy=False, include_omr=False
        )
        batches_sb = pd.read_parquet(d5 / "clean" / "batches.parquet")
        assert batches_sb["published_capacity"].mean() < base_pub_cap * 0.65
    finally:
        shutil.rmtree(d5, ignore_errors=True)

    # 6. neet_sectioned_200: NEET tests use neet_ug_2024_200_sectioned
    d6 = Path(tempfile.mkdtemp(prefix="datamoat_scen_6_"))
    try:
        cfg_6 = load_and_validate_config(scenario_path=SCENARIOS_DIR / "neet_sectioned_200.yaml")
        assert cfg_6["active_knobs"]["neet_variant"] == "sectioned_200"
    finally:
        shutil.rmtree(d6, ignore_errors=True)


# ---------------------------------------------------------------------------
# 11. Performance (tiny < 20s; full < 5 min)
# ---------------------------------------------------------------------------
def test_11_performance_tiny_under_20s() -> None:
    """Verify `tiny` preset completes in < 20s."""
    tmp_dir = Path(tempfile.mkdtemp(prefix="datamoat_perf_tiny_"))
    try:
        t0 = time.perf_counter()
        res = run_datagen_pipeline(seed=42, preset="tiny", out_dir=tmp_dir)
        elapsed = time.perf_counter() - t0
        assert elapsed < 20.0, f"tiny preset took {elapsed:.2f}s >= 20.0s"
        assert res["elapsed_sec"] < 20.0
    finally:
        shutil.rmtree(tmp_dir, ignore_errors=True)


# ---------------------------------------------------------------------------
# 12. Privacy (SYNTHETIC_NAME_LIST_V1 header, synthetic names, 999990xxxx phones)
# ---------------------------------------------------------------------------
def test_12_privacy_synthetic_names_and_phones(full_data_dir: Path) -> None:
    """Verify all names come from SYNTHETIC_NAME_LIST_V1 and all phones match 999990xxxx."""
    assert "SYNTHETIC_NAME_LIST_V1" in SYNTHETIC_HEADER

    students = pd.read_parquet(full_data_dir / "clean" / "students.parquet")
    guardians = pd.read_parquet(full_data_dir / "clean" / "guardians.parquet")
    institutes = pd.read_parquet(full_data_dir / "clean" / "institutes.parquet")

    valid_first_en = {fn for fn, _ in MALE_FIRST_NAMES} | {fn for fn, _ in FEMALE_FIRST_NAMES}
    valid_guard_en = {fn for fn, _, _ in GUARDIAN_FIRST_NAMES}
    valid_sur_en = {sn for sn, _ in SYNTHETIC_SURNAMES}

    for full_name in students["name"].unique():
        parts = str(full_name).split(" ", 1)
        assert len(parts) == 2
        assert parts[0] in valid_first_en, f"Unknown first name {parts[0]}"
        assert parts[1] in valid_sur_en, f"Unknown surname {parts[1]}"

    for g_name in guardians["name"].unique():
        parts = str(g_name).split(" ", 1)
        assert len(parts) == 2
        assert parts[0] in valid_guard_en, f"Unknown guardian first name {parts[0]}"
        assert parts[1] in valid_sur_en, f"Unknown guardian surname {parts[1]}"

    for ph in guardians["phone"].unique():
        ph_str = str(ph)
        assert len(ph_str) == 10 and ph_str.startswith("999990") and ph_str.isdigit(), (
            f"Guardian phone {ph_str} is not in synthetic 999990xxxx range"
        )

    for c_name in institutes["counsellor_name"].unique():
        assert c_name in COUNSELLOR_NAMES

"""Evaluation runner: extraction accuracy, requirement-matching quality, score stability, fabrication catch rate.

Runs on a small synthetic gold set that ships with the repo (deterministic path, no LLM, so results are
reproducible). Extend GOLD_* with real labelled data for the final report.
"""
import random
import re
import time

from app.agents.rules import analyze_jd_rules, extract_facts_rules
from app.engine.matching import match_all
from app.engine.scoring import score
from app.engine.verify import verify_bullet

DOC = """# SkillOra
- Built a multi-agent resume pipeline using CrewAI and Google ADK with a FastAPI backend.
- Reduced resume tailoring time from 40 minutes to 3 minutes per application.
- Implemented a deterministic scoring engine in Python with five weighted components.
- Stored the fact ledger in SQLite using SQLAlchemy.
## Campus Chatbot
- Developed a LangChain chatbot for student queries reaching 91% intent accuracy.
- Deployed the chatbot on Hugging Face Spaces serving 300+ weekly users.
## Internship
- Built REST endpoints with Django REST Framework on PostgreSQL.
- Containerised the service using Docker and ran CI/CD with GitHub Actions.
B.Tech in Computer Science, 2026.
"""
GOLD_FACTS = ["CrewAI", "40 minutes to 3 minutes", "scoring engine", "SQLite", "91%", "300+", "Django REST", "Docker", "B.Tech"]

JD = """Acme is hiring a Backend ML Engineer (0-2 yrs).
Must have: Python, FastAPI, PostgreSQL, Kubernetes, LangChain.
Nice to have: Docker.
B.Tech in CS required."""
GOLD_LABELS = {"Python": "met", "FastAPI": "met", "PostgreSQL": "met", "Kubernetes": "missing", "LangChain": "met", "Docker": "met"}


def _facts_from_doc():
    cands = extract_facts_rules(DOC, "doc.md")
    return [dict(id=f"F{101 + i}", text=c["text"], span=c["span"], project=c["project"], category=c["category"], status="verified", declared=False, source="doc.md") for i, c in enumerate(cands)]


def extraction() -> dict:
    cands = extract_facts_rules(DOC, "doc.md")
    compact = re.sub(r"\s+", " ", DOC)
    valid = sum(1 for c in cands if c["span"] in compact)
    recall = sum(any(g.lower() in c["span"].lower() for c in cands) for g in GOLD_FACTS) / len(GOLD_FACTS)
    return {"label": "Fact-extraction accuracy", "value": round(100 * recall), "detail": f"recall on {len(GOLD_FACTS)} gold facts; span validity {round(100 * valid / max(1, len(cands)))}% ({len(cands)} facts)"}


def matching() -> dict:
    facts = _facts_from_doc()
    a = analyze_jd_rules(JD)
    ms = match_all(a["requirements"], facts)
    got = {m["text"]: m["match"] for m in ms}
    ok = sum(1 for k, v in GOLD_LABELS.items() if got.get(k) == v)
    false_met = sum(1 for k, v in GOLD_LABELS.items() if got.get(k) == "met" and v != "met")
    return {"label": "Requirement-matching quality", "value": round(100 * ok / len(GOLD_LABELS)), "detail": f"{ok}/{len(GOLD_LABELS)} labels correct; {false_met} false 'met'"}


def stability() -> dict:
    facts = _facts_from_doc()
    a = analyze_jd_rules(JD)
    base_bul = [{"id": f"B{i}", "project": f["project"], "text": f["text"], "facts": [f["id"]], "verified": True} for i, f in enumerate(facts[:5])]
    resume = {"summary": "Backend engineer.", "bullets": base_bul}
    projects = [{"id": "P1", "name": "ResCraft", "reason": "", "relevance": 80, "picked": True}]
    totals = set()
    rnd = random.Random(7)
    for _ in range(30):
        fs = facts[:]
        rnd.shuffle(fs)
        totals.add(score(a, match_all(a["requirements"], fs), fs, resume, projects)["total"])
    return {"label": "Score stability (same input)", "value": 100 if len(totals) == 1 else 0, "detail": f"30 runs with shuffled fact order -> {len(totals)} distinct score(s)"}


def fabrication() -> dict:
    facts = _facts_from_doc()
    by = {f["id"]: f for f in facts}
    rnd = random.Random(3)
    fakes = []
    for f in facts:
        nums = re.findall(r"\d+", f["text"])
        if nums:
            n = nums[0]
            fakes.append((f["text"].replace(n, str(int(n) + rnd.choice([7, 15, 40])), 1), [f["id"]]))  # altered metric
        fakes.append((f["text"] + " using Kubernetes and Terraform", [f["id"]]))  # attached wrong technology
        fakes.append(("Led a team of 12 engineers to deliver the platform", [f["id"]]))  # invented claim w/ number
        fakes.append((f["text"], ["F999"]))  # cites non-existent fact
    pend = dict(by)
    pf = dict(facts[0], status="pending")
    pend[pf["id"]] = pf
    fakes.append((pf["text"], [pf["id"]]))  # cites unverified fact
    caught = sum(not verify_bullet(t, ids, pend)["ok"] for t, ids in fakes)
    honest = sum(verify_bullet(f["text"], [f["id"]], by)["ok"] for f in facts)
    return {"label": "Fabrication catch rate", "value": round(100 * caught / len(fakes)), "detail": f"{caught}/{len(fakes)} fabricated claims blocked; {honest}/{len(facts)} honest bullets allowed"}


def ndcg_at_k(rels: list[float], k: int) -> float:
    """NDCG@K = DCG@K / IDCG@K with gain (2^rel - 1) / log2(position + 1)."""
    import math

    def dcg(xs):
        return sum((2 ** r - 1) / math.log2(i + 2) for i, r in enumerate(xs[:k]))

    ideal = dcg(sorted(rels, reverse=True))
    return dcg(rels) / ideal if ideal else 0.0


GOLD_PROJECT_REL = {"SkillOra": 3, "Internship": 2, "Campus Chatbot": 1}  # hand-labelled for the synthetic document above


def ranking() -> dict:
    """How well does the Project Selector order projects compared with the reference relevance labels?"""
    from app.service import select_projects

    facts = _facts_from_doc()
    a = analyze_jd_rules(JD)
    ms = match_all(a["requirements"], facts)
    ranked = [p["name"] for p in select_projects(a, ms, facts)]
    rels = [GOLD_PROJECT_REL.get(n, 0) for n in ranked]
    n = ndcg_at_k(rels, 3)
    return {"label": "Project ranking quality (NDCG@3)", "value": round(100 * n), "detail": f"order {ranked} vs reference labels {GOLD_PROJECT_REL}"}


def run_all() -> dict:
    t = time.time()
    rows = [extraction(), matching(), stability(), fabrication(), ranking()]
    return {"metrics": rows, "seconds": round(time.time() - t, 2), "note": "Synthetic gold set, deterministic (no-LLM) path. Replace with labelled real data for the final report."}


if __name__ == "__main__":
    import json

    print(json.dumps(run_all(), indent=2))

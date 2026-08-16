"""
Haystack tags -> Brick classes. Not a general ontology mapper - a small,
first-match-wins rule engine over marker-tag SETS (see
rules/haystack_to_brick.yaml), because that's literally what the earlier
"how do we get something in Haystack but not in Brick into Brick" question
needs and nothing more.
"""

import os

import yaml
from rdflib import RDF, RDFS, SKOS, Literal, URIRef

from timberdoodle import tracing
from timberdoodle.store import BRICK, PROJ, TD

tracer = tracing.get_tracer(__name__)

DEFAULT_RULES_PATH = os.path.join(os.path.dirname(__file__), "..", "..", "rules", "haystack_to_brick.yaml")

# Below this, an LLM guess is discarded rather than asserted - see
# classify_point_with_fallback. Not exposed as a config knob; there's
# nothing here yet that justifies making it one.
LLM_CONFIDENCE_THRESHOLD = 0.7


def load_rules(path: str = DEFAULT_RULES_PATH) -> list[dict]:
    with open(path) as f:
        return yaml.safe_load(f)["rules"]


def read_tags(store, point_uri) -> set[str]:
    rows = store.query(f"""
        PREFIX haystack: <urn:timberdoodle:haystack#>
        SELECT ?tag WHERE {{ <{point_uri}> haystack:hasTag ?tag }}
    """)
    return {str(r.tag) for r in rows}


def classify_point(store, point_uri, rules: list[dict] | None = None) -> tuple[str, str | None]:
    """Three outcomes:

    1. **Direct**: some rule's tags are a SUBSET of this point's tags -> the
       real Brick class directly. Subset, not exact-equality: a real point
       always carries extra structural tags (`point`, `cur`, `dis`, `kind`,
       `unit`, ...) alongside the domain-specific markers a rule cares
       about, and none of that extra information should demote a clean
       match to a fallback. When multiple rules qualify, the most specific
       (largest tag set) wins.
    2. **Fallback**: no rule's tags are a full subset, but at least one rule
       shares SOME tags with this point (e.g. `zone`/`air`/`sensor` present
       but `temp` isn't - a CO2 sensor tagged in the same structural family
       as our one temp-sensor rule) -> a PROJ class, subClassOf the
       best-overlapping rule's Brick class. Lossless: the raw
       HAYSTACK:hasTag triples are never touched, so nothing not covered by
       a rule is dropped on the floor.
    3. **Miss**: no overlap with any rule at all -> TD:UnmappedPoint.
    """
    if rules is None:
        rules = load_rules()

    with tracer.start_as_current_span("mapping.classify_point") as span:
        span.set_attribute("point_uri", str(point_uri))
        tags = read_tags(store, point_uri)

        direct_matches = [r for r in rules if set(r["tags"]) <= tags]
        if direct_matches:
            rule = max(direct_matches, key=lambda r: len(r["tags"]))
            store.add_entity(point_uri, BRICK[rule["brick_class"]])
            span.set_attribute("outcome", "direct")
            span.set_attribute("matched_rule", rule["brick_class"])
            return "direct", rule["brick_class"]

        overlaps = [(len(set(r["tags"]) & tags), r) for r in rules]
        overlaps = [(score, r) for score, r in overlaps if score > 0]
        if overlaps:
            _, rule = max(overlaps, key=lambda pair: pair[0])
            extra = sorted(t.capitalize() for t in tags - set(rule["tags"]))
            proj_class = f"{rule['brick_class']}_{'_'.join(extra)}" if extra else f"{rule['brick_class']}_Variant"
            store.add_entity(point_uri, PROJ[proj_class])
            store.add_relationship(PROJ[proj_class], RDFS.subClassOf, BRICK[rule["brick_class"]])
            # Brick's own extension guidance (docs.brickschema.org/extra/extending.html)
            # asks for a skos:definition on any proprietary class - so a human
            # reading the graph later sees *why* this PROJ class exists
            # (which tags produced it) without re-deriving it from the rules file.
            store.add_relationship(PROJ[proj_class], SKOS.definition, Literal(", ".join(sorted(tags))))
            span.set_attribute("outcome", "fallback")
            span.set_attribute("matched_rule", rule["brick_class"])
            return "fallback", rule["brick_class"]

        store.add_entity(point_uri, TD.UnmappedPoint)
        span.set_attribute("outcome", "miss")
        span.set_attribute("matched_rule", "")
        return "miss", None


def classify_point_with_fallback(store, point_uri, rules: list[dict] | None = None, llm_classify=None) -> tuple[str, str | None]:
    """classify_point, with an injectable LLM fallback for what the rule
    engine can't place. Rule engine runs first, always - llm_classify (see
    llm_classifier.classify_with_llm) is only ever consulted on a
    "fallback"/"miss" outcome, and llm_classify=None (the default) means
    this behaves exactly like classify_point - mapping.py itself has no
    hard dependency on the LLM classifier module or the `anthropic`
    package. A low-confidence LLM guess is never applied: whatever
    classify_point already produced (a PROJ fallback class, or
    TD.UnmappedPoint) is left untouched rather than silently overwritten."""
    with tracer.start_as_current_span("mapping.classify_point_with_fallback") as span:
        outcome, brick_class = classify_point(store, point_uri, rules)
        span.set_attribute("rule_outcome", outcome)
        if outcome == "direct" or llm_classify is None:
            return outcome, brick_class

        if rules is None:
            rules = load_rules()
        tags = read_tags(store, point_uri)
        rows = store.query(f"SELECT ?topic WHERE {{ <{point_uri}> <{TD.sourceTopic}> ?topic }}")
        label = next((str(r.topic) for r in rows), None)
        known_classes = sorted({r["brick_class"] for r in rules})

        result = llm_classify(tags, label, None, known_classes)
        span.set_attribute("llm_brick_class", result.brick_class)
        span.set_attribute("llm_confidence", result.confidence)
        if result.confidence < LLM_CONFIDENCE_THRESHOLD:
            span.set_attribute("outcome", outcome)
            return outcome, brick_class

        store.add_entity(point_uri, BRICK[result.brick_class])
        store.add_relationship(point_uri, SKOS.definition, Literal(f"llm-classified: {result.reasoning}"))
        span.set_attribute("outcome", "llm")
        return "llm", result.brick_class


def reclassify(store, uri, rules: list[dict] | None = None) -> tuple[str, str | None]:
    """classify_point is deliberately pure-additive (existing callers rely
    on that), which means calling it twice for the same URI with a
    different result - a rules file change, a human correcting a mistake -
    leaves both the old and new rdf:type asserted rather than replacing.
    This is the explicit "I want this entity's classification refreshed"
    operation: remove whatever classify_point itself would have asserted
    last time (a BRICK class, a PROJ class, or TD:UnmappedPoint - never
    anything outside those three namespaces, so this never touches a type
    triple this function didn't put there), then classify fresh.

    Deliberately doesn't touch a PROJ class's own subClassOf/skos:definition
    triples - other entities may share that same PROJ class, so only the
    uri's own rdf:type edge into it is this function's business."""
    with tracer.start_as_current_span("mapping.reclassify") as span:
        span.set_attribute("uri", str(uri))
        existing_types = store.query(f"SELECT ?type WHERE {{ <{uri}> a ?type }}")
        for row in existing_types:
            t = URIRef(str(row.type))
            if str(t).startswith(str(BRICK)) or str(t).startswith(str(PROJ)) or t == TD.UnmappedPoint:
                store.remove_relationship(uri, RDF.type, t)
        return classify_point(store, uri, rules)

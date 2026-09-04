//! Lecture des décisions (détail, sections, similaires).

use std::collections::{HashMap, HashSet};

use lj_core::decision::Decision;
use lj_core::truecase;
use lj_dtos::{
    CitationSpan, CitationTarget, DecisionDetail, DecisionPreview, DecisionSection,
    DecisionSourceXml, FacetTag, JurisdictionType, LegalRefArticle, LegalReference,
    SimilarDecisionHit, SimilarDecisionsResponse,
};

use tracing::instrument;

use crate::error::{ApiError, Result};
use crate::referential::{referential, Referential};
use crate::state::AppState;

/// Facteur d'élargissement de la fenêtre ANN interne.
const SIMILAR_INNER_LIMIT_FACTOR: i64 = 24;

/// Sur-fetch du volet espèce : absorbe les exclusions avant troncature à `limit`.
const ESPECE_OVERFETCH_FACTOR: i64 = 3;

/// Probes vchordrq de la jambe KNN pré-filtrée portée notable.
const PRINCIPE_KNN_PROBES: u32 = 100;

/// Plafond du bloc « citée par les analyses ». Mesuré : 1,5 citation entrante en
/// moyenne sur 6 417 décisions citées, 66 pour la plus citée, une seule au-delà
/// de 50. Le bloc tronque en silence, donc il tient au-dessus du maximum observé.
const RENVOYANTS_LIMIT: i64 = 100;

/// Page de tête du bloc « citée par ». Mesuré le 23/08 sur 258 372 décisions
/// citées : une citante médiane, 31 au 99e centile, 8 074 pour la plus citée. Le
/// total accompagne la liste, faute de facette où poursuivre la postérité.
const CITANTES_LIMIT: i64 = 5;

/// Codes de publication « portée notable » = MAJEURE ∪ IMPORTANTE.
const NOTABLE_CODES: [&str; 8] = ["r", "A", "b", "l", "c", "B", "C+", "R"];

/// Jambe IDF : nombre max de termes article retenus sur la décision source.
const IDF_MAX_RARE_TERMS: i64 = 8;

/// Jambe IDF : df au-delà duquel un article est trop cité pour signer la
/// question de droit.
const IDF_RARE_DF_CAP: i64 = 100_000;

/// Titres de sommaire canoniques par `kind`.
fn section_label(kind: &str) -> Option<&'static str> {
    match kind {
        "preamble" => Some("Introduction"),
        "procedure" => Some("Procédure"),
        "visa" => Some("Visa"),
        "expose" => Some("Exposé du litige"),
        "moyens" => Some("Moyens"),
        "motivations" => Some("Motivations"),
        "dispositif" => Some("Dispositif"),
        _ => None,
    }
}

/// Paragraphes du corps : lignes non vides du texte nettoyé.
pub fn decision_paragraphs(decision: &Decision) -> Vec<String> {
    decision
        .texte_integral_clean
        .lines()
        .map(str::trim)
        .filter(|line| !line.is_empty())
        .map(str::to_string)
        .collect()
}

/// Plage globale `[start, end)` (codepoints sur `texte_integral_clean` =
/// `decisions.full_text`) de chaque paragraphe rendu, alignée index-à-index sur
/// `paragraphs`. Paragraphe introuvable ⇒ plage dégénérée `(cursor, cursor)`, à
/// laquelle aucun span ne se rattache.
///
/// Le curseur porte l'offset codepoint ET l'offset octet : seul l'écart depuis
/// le curseur est recompté. Repartir de l'octet 0 à chaque paragraphe coûtait
/// 6,7 s sur 227 k caractères et 3 000 lignes.
fn paragraph_global_ranges(text: &str, paragraphs: &[String]) -> Vec<(usize, usize)> {
    let mut char_cursor = 0usize;
    let mut byte_cursor = 0usize;
    let mut ranges = Vec::with_capacity(paragraphs.len());
    for paragraph in paragraphs {
        match text[byte_cursor..].find(paragraph.as_str()) {
            Some(gap) => {
                let start = char_cursor + text[byte_cursor..byte_cursor + gap].chars().count();
                let end = start + paragraph.chars().count();
                byte_cursor += gap + paragraph.len();
                char_cursor = end;
                ranges.push((start, end));
            }
            None => ranges.push((char_cursor, char_cursor)),
        }
    }
    ranges
}

fn decision_source_meta(decision: &Decision) -> DecisionSourceXml {
    DecisionSourceXml {
        nom_jurisdiction_type: decision.jurisdiction_name.clone(),
        numero_dossier: decision.numero_dossier.clone(),
        date_lecture: decision.date_lecture.clone(),
        formation_jugement: decision.formation.clone(),
        type_recours: decision.type_recours.clone(),
        solution: decision.solution.clone(),
    }
}

/// Replie la structure autoritative (`decision.sections`) en blocs de
/// paragraphes pour le sommaire/corps front.
///
/// Chaque paragraphe est rattaché — par ses offsets char — à la section
/// canonique qui le couvre, en partition stricte. Les paragraphes sont émis
/// dans l'ordre du texte ; seuls les runs consécutifs de même `kind` sont
/// fusionnés. `None` quand aucune section autoritative (`start_char >= 0`)
/// n'existe.
pub fn sections_from_decision(
    decision: &Decision,
    paragraphs: &[String],
    ranges: &[(usize, usize)],
    citations: &[GlobalCitation],
) -> Option<Vec<DecisionSection>> {
    // (start_char, end_char, kind, label), trié par start_char.
    let mut bounds: Vec<(usize, usize, &str, &str)> = decision
        .sections
        .iter()
        .map(|s| (s.start_char, s.end_char, s.kind.as_str(), s.label.as_str()))
        .collect();
    bounds.sort_by_key(|b| b.0);

    if bounds.is_empty() {
        return None;
    }

    let section_for = |pos: usize| -> (&str, String) {
        let mut chosen = &bounds[0];
        for bound in &bounds {
            if bound.0 <= pos {
                chosen = bound;
            } else {
                break;
            }
        }
        let kind = chosen.2;
        let label = section_label(kind)
            .map(str::to_string)
            .unwrap_or_else(|| chosen.3.to_string());
        (kind, label)
    };

    let mut out: Vec<DecisionSection> = Vec::new();
    // Plages globales alignées sur `out[i].paragraphs[j]`.
    let mut out_ranges: Vec<Vec<(usize, usize)>> = Vec::new();
    let mut seen_kinds: HashMap<String, usize> = HashMap::new();

    for (paragraph, &range) in paragraphs.iter().zip(ranges) {
        let pos = range.0;
        let (kind, label) = section_for(pos);

        if let Some(last) = out.last_mut() {
            if last.kind == kind {
                last.paragraphs.push(paragraph.clone());
                out_ranges
                    .last_mut()
                    .expect("out_ranges aligné sur out")
                    .push(range);
                continue;
            }
        }

        let count = seen_kinds.entry(kind.to_string()).or_insert(0);
        *count += 1;
        let anchor = if *count == 1 {
            kind.to_string()
        } else {
            format!("{kind}-{count}")
        };
        out.push(DecisionSection {
            kind: kind.to_string(),
            anchor,
            label,
            paragraphs: vec![paragraph.clone()],
            paragraph_spans: Vec::new(),
        });
        out_ranges.push(vec![range]);
    }

    if out.is_empty() {
        return None;
    }

    for (section, ranges) in out.iter_mut().zip(&out_ranges) {
        let spans: Vec<Vec<CitationSpan>> = ranges
            .iter()
            .map(|&(pstart, pend)| spans_for_range(citations, pstart, pend))
            .collect();
        if spans.iter().any(|s| !s.is_empty()) {
            section.paragraph_spans = spans;
        }
    }

    Some(out)
}

/// Une citation globale prête à projeter : `[global_start, global_end)` en
/// codepoints sur `texte_integral_clean` (= `decisions.full_text`) et ses cibles
/// résolues (une seule pour une mention simple ; toutes les bornes +
/// intermédiaires pour une plage fusionnée).
#[derive(Debug, Clone)]
pub struct GlobalCitation {
    pub start: usize,
    pub end: usize,
    pub targets: Vec<CitationTarget>,
}

/// Une mention liée brute : une ligne `legal_citation` résolue.
struct RawCite {
    start: usize,
    end: usize,
    text_uid: String,
    slug: String,
    num_key: Option<String>,
    href: String,
    label: String,
    /// Span « N et suivants » : la cible est la famille TOC de l'ancre, résolue à
    /// l'assemblage.
    suivants: bool,
}

/// Deux mentions adjacentes forment-elles une plage d'articles
/// (« L. 225-1 à L. 225-9 ») ? Bornes du MÊME texte, toutes deux à article,
/// séparées du seul mot « à ».
fn is_article_range(a: &RawCite, b: &RawCite, text: &[char]) -> bool {
    a.num_key.is_some()
        && b.num_key.is_some()
        && a.text_uid == b.text_uid
        && b.start > a.end
        && b.start - a.end <= 8
        && text
            .get(a.end..b.start)
            .is_some_and(|gap| gap.iter().collect::<String>().trim() == "à")
}

/// Décompose une paire de bornes en `(radical, k1, k2)` quand la plage est
/// énumérable : même radical avant le dernier composant, composants finaux
/// entiers croissants (« L. 225-1 » / « L. 225-9 » → `("L. 225", 1, 9)` ;
/// « 102 » / « 108 » → `("", 102, 108)`). Bornes à suffixe non numérique
/// (« 50 sexies B à H ») ou radicaux différents → `None`, la plage reste aux
/// bornes. Cap à 50.
fn range_stem(num1: &str, num2: &str) -> Option<(String, u32, u32)> {
    fn split(num: &str) -> (&str, Option<u32>) {
        match num.rfind(['-', ' ']) {
            Some(i) => (&num[..i], num[i + 1..].parse().ok()),
            None => ("", num.parse().ok()),
        }
    }
    let (stem1, k1) = split(num1);
    let (stem2, k2) = split(num2);
    let (k1, k2) = (k1?, k2?);
    (stem1 == stem2 && k1 < k2 && k2 - k1 <= 50).then(|| (stem1.to_string(), k1, k2))
}

/// Clés candidates des articles intermédiaires d'une plage : les entiers
/// stricts entre les bornes (`exact`) et les sous-articles insérés de chaque
/// pas (`like`, « L. 225-3-1 » ; le pas de la borne basse est inclus, pas celui
/// de la borne haute).
fn range_candidate_keys(stem: &str, k1: u32, k2: u32) -> (Vec<String>, Vec<String>) {
    let key = |k: u32| {
        if stem.is_empty() {
            k.to_string()
        } else {
            format!("{stem}-{k}")
        }
    };
    let exact: Vec<String> = (k1 + 1..k2).map(key).collect();
    let like: Vec<String> = (k1..k2).map(|k| format!("{}-%", key(k))).collect();
    (exact, like)
}

/// Projette les citations globales tombant dans `[pstart, pend)` en spans LOCAUX
/// au paragraphe (offsets ramenés à `pstart`), demi-ouverts. Une citation n'est
/// retenue que si elle est entièrement contenue dans le paragraphe.
///
/// Chevauchement entre mentions → fusion en leur enveloppe avec union des
/// cibles (dédup par `(href, label)`) : un span pour N cibles, que le front rend
/// en lien simple pour 1 cible et en menu déroulant pour ≥ 2. Les spans rendus
/// sont triés par début, disjoints.
fn spans_for_range(citations: &[GlobalCitation], pstart: usize, pend: usize) -> Vec<CitationSpan> {
    let mut cands: Vec<(usize, usize, &GlobalCitation)> = citations
        .iter()
        .filter(|c| c.start >= pstart && c.end <= pend && c.end > c.start)
        .map(|c| (c.start - pstart, c.end - pstart, c))
        .collect();
    cands.sort_by(|a, b| a.0.cmp(&b.0).then(a.1.cmp(&b.1)));

    let mut kept: Vec<CitationSpan> = Vec::new();
    for (ls, le, c) in cands {
        match kept.last_mut() {
            Some(last) if ls < last.end => {
                last.end = last.end.max(le);
                for target in &c.targets {
                    if !last.targets.contains(target) {
                        last.targets.push(target.clone());
                    }
                }
            }
            _ => kept.push(CitationSpan {
                start: ls,
                end: le,
                targets: c.targets.clone(),
            }),
        }
    }
    kept
}

/// Spans cliquables alignés sur [`decision_paragraphs`] (corps plat, sans
/// sections autoritatives).
fn flat_paragraph_spans(
    ranges: &[(usize, usize)],
    citations: &[GlobalCitation],
) -> Vec<Vec<CitationSpan>> {
    let spans: Vec<Vec<CitationSpan>> = ranges
        .iter()
        .map(|&(pstart, pend)| spans_for_range(citations, pstart, pend))
        .collect();
    if spans.iter().any(|s| !s.is_empty()) {
        spans
    } else {
        Vec::new()
    }
}

/// Une référence brute lue de la DB : `(instrument, slug résolu, [(num affiché,
/// ref_num_key résolu)])`. `None` = non ancré au catalogue, donc pas de lien.
type RawLegalRef = (String, Option<String>, Vec<(String, Option<String>)>);

/// Construit les `LegalReference` exposées.
///
/// Un instrument cité sans article précis est conservé tel quel. Le `slug` et le
/// `numKey` résolus sont propagés au DTO pour bâtir les liens
/// `/texte/{slug}/{numKey}` sans re-slugifier côté front. `None` si la liste
/// résultante est vide.
fn parse_legal_refs(raw: &[RawLegalRef]) -> Option<Vec<LegalReference>> {
    if raw.is_empty() {
        return None;
    }
    let mut refs: Vec<LegalReference> = Vec::new();
    for (instrument, slug, original) in raw {
        if slug.is_none() {
            continue;
        }
        let mut seen = std::collections::HashSet::new();
        let articles: Vec<LegalRefArticle> = original
            .iter()
            .filter(|(num, _)| seen.insert(num.clone()))
            .map(|(num, num_key)| LegalRefArticle {
                num: num.clone(),
                num_key: num_key.clone().unwrap_or_default(),
            })
            .collect();
        refs.push(LegalReference {
            instrument: instrument.clone(),
            slug: slug.clone(),
            articles,
        });
    }
    if refs.is_empty() {
        None
    } else {
        Some(refs)
    }
}

fn parse_jur_type(raw: &str) -> Result<JurisdictionType> {
    match raw {
        "TA" => Ok(JurisdictionType::Ta),
        "CAA" => Ok(JurisdictionType::Caa),
        "CE" => Ok(JurisdictionType::Ce),
        "CONSTIT" => Ok(JurisdictionType::Constit),
        "TC" => Ok(JurisdictionType::Tc),
        "CC" => Ok(JurisdictionType::Cc),
        "CA" => Ok(JurisdictionType::Ca),
        "TJ" => Ok(JurisdictionType::Tj),
        "TCOM" => Ok(JurisdictionType::Tcom),
        "CEDH" => Ok(JurisdictionType::Cedh),
        "CJUE" => Ok(JurisdictionType::Cjue),
        "CNDA" => Ok(JurisdictionType::Cnda),
        "CNIL" => Ok(JurisdictionType::Cnil),
        other => Err(ApiError::Internal(format!(
            "jurisdiction_type DB invalide : {other:?}"
        ))),
    }
}

/// Tag référentiel d'un uid optionnel (`solution:REJET` → `{REJET, Rejet}`).
fn opt_tag(uid: &Option<String>, refs: &Referential) -> Option<FacetTag> {
    uid.as_deref().map(|u| refs.tag(u))
}

/// Projette `themes` depuis `source_fields` : casefold + déduplication
/// ordre-stable, entrées vides retirées. Scalaire au lieu de liste, ou clé
/// absente ⇒ `Vec` vide.
fn project_themes(source_fields: &serde_json::Value) -> Vec<String> {
    let Some(arr) = source_fields.get("themes").and_then(|v| v.as_array()) else {
        return Vec::new();
    };
    let mut seen: std::collections::HashSet<String> = std::collections::HashSet::new();
    let mut out: Vec<String> = Vec::new();
    for v in arr {
        let Some(s) = v.as_str() else { continue };
        let theme = s.trim();
        if theme.is_empty() {
            continue;
        }
        if seen.insert(theme.to_lowercase()) {
            out.push(theme.to_string());
        }
    }
    out
}

/// Projette `nac` depuis `source_fields` : le littéral chaîne `"null"` et la
/// chaîne vide → `None` ; code brut sinon.
fn project_nac(source_fields: &serde_json::Value) -> Option<String> {
    let s = source_fields.get("nac")?.as_str()?.trim();
    if s.is_empty() || s == "null" {
        return None;
    }
    Some(s.to_string())
}

/// Triplet hydraté depuis la `Decision` reconstruite : paragraphes, sections,
/// méta XML.
type ParsedPayload = (
    Vec<String>,
    Vec<Vec<CitationSpan>>,
    Option<Vec<DecisionSection>>,
    Option<DecisionSourceXml>,
);

/// Détail complet d'une décision par `public_id` (paragraphes, sections, refs).
#[instrument(skip(state), fields(db.system = "postgresql", public_id = %public_id))]
pub async fn get_decision(state: &AppState, public_id: &str) -> Result<DecisionDetail> {
    let refs = referential(state).await?;
    let conn = state.pool.get().await?;

    let row = conn
        .query_opt(
            "
            SELECT
              d.id,
              d.public_id,
              d.jurisdiction_type,
              d.full_text,
              ds.source_fields,
              d.solution_uid,
              d.procedure_uid,
              d.office_uid,
              d.legal_domain_uid,
              d.publication_codes,
              d.date_lecture::text,
              d.date_audience::text,
              d.jurisdiction_code,
              d.docket_numbers,
              d.seat,
              d.summary,
              d.ecli,
              ds.source,
              d.formation_uid,
              ariane.source_fields,
              notes.files,
              web.notes,
              ds.source_uid,
              d.case_name,
              d.seat_paths
            FROM decisions d
            LEFT JOIN LATERAL (
                SELECT source_fields, source, source_uid
                FROM decision_sources
                WHERE decision_id = d.id AND deleted_at IS NULL
                ORDER BY source_rank DESC, (lang = 'fra') IS TRUE DESC, source_uid ASC
                LIMIT 1
            ) ds ON true
            LEFT JOIN LATERAL (
                SELECT source_fields
                FROM decision_sources
                WHERE decision_id = d.id AND deleted_at IS NULL
                  AND source = 'ariane-web'
                LIMIT 1
            ) ariane ON true
            LEFT JOIN LATERAL (
                SELECT source_fields->'files' AS files
                FROM decision_sources
                WHERE decision_id = d.id AND deleted_at IS NULL
                  AND source = 'judilibre'
                  AND jsonb_array_length(COALESCE(source_fields->'files', '[]'::jsonb)) > 0
                LIMIT 1
            ) notes ON true
            LEFT JOIN LATERAL (
                SELECT jsonb_agg(c) AS notes
                FROM decision_sources ds3
                CROSS JOIN LATERAL jsonb_array_elements(ds3.source_fields->'commentaires') c
                WHERE ds3.decision_id = d.id AND ds3.deleted_at IS NULL
                  AND ds3.source <> 'ariane-web'
                  AND jsonb_typeof(ds3.source_fields->'commentaires') = 'array'
            ) web ON true
            WHERE d.public_id = $1
            ",
            &[&public_id],
        )
        .await?;

    let row = row.ok_or(ApiError::NotFound)?;

    let decision_id: i64 = row.get(0);
    let id: String = row.get(1);
    let jur_type_raw: String = row.get(2);
    let full_text: Option<String> = row.get(3);
    let source_fields: Option<serde_json::Value> = row.get(4);
    let solution_uid: Option<String> = row.get(5);
    let procedure_uid: Option<String> = row.get(6);
    let office_uid: Option<String> = row.get(7);
    let legal_domain_uid: Option<String> = row.get(8);
    let publication_codes: Vec<String> = row.get(9);
    let date_lecture: Option<String> = row.get(10);
    let date_audience: Option<String> = row.get(11);
    let jurisdiction_code: Option<String> = row.get(12);
    let docket_numbers_raw: Option<Vec<String>> = row.get(13);
    let seat_stored: Option<lj_core::chamber::Seat> = row
        .get::<_, Option<tokio_postgres::types::Json<lj_core::chamber::Seat>>>(14)
        .map(|j| j.0);
    let seat_paths: Vec<String> = row.get::<_, Option<Vec<String>>>(24).unwrap_or_default();
    let summary: Option<String> = row.get(15);
    let ecli: Option<String> = row.get(16);
    let source: Option<String> = row.get(17);
    let formation_uid: Option<String> = row.get(18);
    let ariane_bundle: Option<serde_json::Value> = row.get(19);
    let judilibre_files: Option<serde_json::Value> = row.get(20);
    let web_notes: Option<serde_json::Value> = row.get(21);
    let source_uid: Option<String> = row.get(22);
    let case_name: Option<String> = row.get(23);

    let jur_type = parse_jur_type(&jur_type_raw)?;
    let jurisdiction_name = jurisdiction_code
        .as_deref()
        .and_then(|c| refs.jurisdiction(c))
        .map(|j| j.label.clone());

    let ref_rows = conn
        .query(
            "
            SELECT lt.title AS instrument,
                   lt.slug,
                   lt.text_uid,
                   COALESCE(array_agg(DISTINCT el->>3 ORDER BY el->>3)
                            FILTER (WHERE el->>3 IS NOT NULL),
                            ARRAY[]::text[]) AS num_keys
            FROM legal_citation lc
            CROSS JOIN LATERAL jsonb_array_elements(lc.spans) AS el
            JOIN legal_text lt ON lt.text_uid = el->>2
            WHERE lc.decision_id = $1
            GROUP BY lt.text_uid, lt.title, lt.slug
            ORDER BY 1
            ",
            &[&decision_id],
        )
        .await?;

    let span_rows = conn
        .query(
            "
            SELECT (el->>0)::int AS char_start,
                   (el->>1)::int AS char_end,
                   lt.text_uid,
                   lt.slug,
                   el->>3 AS ref_num_key,
                   lt.title AS label,
                   (EXISTS (SELECT 1 FROM legal_article a
                            WHERE a.text_uid = lt.text_uid)
                    OR coalesce(length(lt.body), 0) > 0) AS readable,
                   (el->>4)::bool AS suivants
            FROM legal_citation lc
            CROSS JOIN LATERAL jsonb_array_elements(lc.spans) AS el
            JOIN legal_text lt ON lt.text_uid = el->>2
            WHERE lc.decision_id = $1
            ",
            &[&decision_id],
        )
        .await?;

    let case_rows = conn
        .query(
            "
            SELECT cc.char_start,
                   cc.char_end,
                   t.public_id,
                   t.jurisdiction_code,
                   t.date_lecture::text,
                   t.docket_numbers
            FROM case_citation cc
            JOIN decisions t ON t.id = cc.target_decision_id
            WHERE cc.decision_id = $1 AND t.deleted_at IS NULL
            ",
            &[&decision_id],
        )
        .await?;

    // Le lien de citation porte la date de lecture : il sert la version que la
    // décision appliquait. Sans elle, 5,1 % des liens rendent un texte que la cour
    // n'a pas appliqué, l'article ayant reçu une version depuis, et sans le dire.
    let cite_date = date_lecture.clone();
    let article_href = |slug: &str, num_key: &str| match cite_date.as_deref() {
        Some(d) => format!("/texte/{slug}/{num_key}/{d}"),
        None => format!("/texte/{slug}/{num_key}"),
    };

    let mut raw: Vec<RawCite> = span_rows
        .iter()
        .filter_map(|r| {
            let start: i32 = r.get(0);
            let end: i32 = r.get(1);
            let text_uid: String = r.get(2);
            let slug: Option<String> = r.get(3);
            let num_key: Option<String> = r.get(4);
            let label: String = r.get(5);
            let readable: bool = r.get(6);
            let suivants: bool = r.get(7);
            let slug = slug?;
            let num_key = num_key.filter(|k| !k.is_empty());
            let href = match num_key.as_deref() {
                Some(k) => article_href(&slug, k),
                None if readable => format!("/texte/{slug}"),
                None => return None,
            };
            Some(RawCite {
                start: start.max(0) as usize,
                end: end.max(0) as usize,
                text_uid,
                slug,
                num_key,
                href,
                label,
                suivants,
            })
        })
        .collect();
    raw.sort_by_key(|c| c.start);

    let text_chars: Vec<char> = full_text.as_deref().unwrap_or_default().chars().collect();

    // Plages d'articles (« L. 225-1 à L. 225-9 ») : la capture pose une ligne par
    // borne écrite ; la plage — un span de borne à borne — est reconstituée ici, et
    // ses articles intermédiaires résolus contre le catalogue.
    let single = |c: &RawCite| CitationTarget {
        href: Some(c.href.clone()),
        label: c.label.clone(),
    };
    let mut citations: Vec<GlobalCitation> = Vec::with_capacity(raw.len());
    // Membres des plages recollées (bornes + intermédiaires), par `text_uid` : ils
    // rejoignent la liste « Références juridiques » du texte cité.
    let mut range_members: std::collections::HashMap<String, Vec<String>> =
        std::collections::HashMap::new();
    let mut it = raw.into_iter().peekable();
    while let Some(a) = it.next() {
        let ranged = it
            .peek()
            .is_some_and(|b| is_article_range(&a, b, &text_chars));
        if !ranged {
            // « N et suivants » : la famille TOC de l'ancre en menu, comme une plage.
            // `_suivants_family_keys` porte la sémantique (section unique, arête en vigueur
            // à la date de lecture de la décision, cap 20 ; NULL sinon, l'ancre reste alors
            // un lien simple). Les clés publiques de la famille repassent en numéro
            // d'affichage (`legal_article.num`).
            let family: Vec<String> = match (a.suivants, a.num_key.as_deref()) {
                (true, Some(nk)) => conn
                    .query(
                        "
                        SELECT coalesce(
                                 (SELECT la.num FROM legal_article la
                                  WHERE la.text_uid = $1 AND la.num_key = t.k
                                  ORDER BY la.date_debut DESC LIMIT 1), t.k)
                        FROM unnest(_suivants_family_keys($1, $2,
                                 (SELECT coalesce(d.date_lecture, CURRENT_DATE)
                                  FROM decisions d WHERE d.id = $3)))
                             WITH ORDINALITY AS t(k, ord)
                        ORDER BY t.ord
                        ",
                        &[
                            &a.text_uid,
                            &lj_core::article_key::article_key(nk),
                            &decision_id,
                        ],
                    )
                    .await?
                    .iter()
                    .map(|r| r.get(0))
                    .collect(),
                _ => Vec::new(),
            };
            let targets = if family.is_empty() {
                vec![single(&a)]
            } else {
                let members = range_members.entry(a.text_uid.clone()).or_default();
                members.extend(family.iter().cloned());
                family
                    .iter()
                    .map(|nk| CitationTarget {
                        href: Some(article_href(
                            &a.slug,
                            &lj_core::article_key::article_key(nk),
                        )),
                        label: format!("{nk} — {}", a.label),
                    })
                    .collect()
            };
            citations.push(GlobalCitation {
                start: a.start,
                end: a.end,
                targets,
            });
            continue;
        }
        let b = it.next().expect("peek a garanti un suivant");
        // Intermédiaires = clés numériquement entre les bornes ET existantes au
        // catalogue, sous-articles insérés compris. Bornes non énumérables
        // (« 50 sexies B à H ») → la plage garde ses deux bornes.
        let mut inter: Vec<String> = Vec::new();
        if let Some((stem, k1, k2)) = range_stem(
            a.num_key.as_deref().expect("gardé par is_article_range"),
            b.num_key.as_deref().expect("gardé par is_article_range"),
        ) {
            let (exact, like) = range_candidate_keys(&stem, k1, k2);
            inter = conn
                .query(
                    "
                    SELECT DISTINCT num_key FROM legal_article
                    WHERE text_uid = $1 AND (num_key = ANY($2) OR num_key LIKE ANY($3))
                    ",
                    &[&a.text_uid, &exact, &like],
                )
                .await?
                .iter()
                .map(|r| r.get::<_, String>(0))
                .collect();
            inter.sort_by_key(|nk| {
                let tail = nk.strip_prefix(&stem).unwrap_or(nk);
                let k: u32 = tail
                    .trim_start_matches(['-', ' '])
                    .split('-')
                    .next()
                    .and_then(|c| c.parse().ok())
                    .unwrap_or(0);
                (k, nk.clone())
            });
        }
        let bound = |c: &RawCite| CitationTarget {
            href: Some(c.href.clone()),
            label: format!(
                "{} — {}",
                lj_core::article_key::display(
                    c.num_key.as_deref().expect("gardé par is_article_range")
                ),
                c.label
            ),
        };
        let members = range_members.entry(a.text_uid.clone()).or_default();
        members.push(a.num_key.clone().expect("gardé par is_article_range"));
        members.extend(inter.iter().cloned());
        members.push(b.num_key.clone().expect("gardé par is_article_range"));
        let mut targets = vec![bound(&a)];
        targets.extend(inter.into_iter().map(|nk| CitationTarget {
            href: Some(article_href(&a.slug, &nk)),
            label: format!("{} — {}", lj_core::article_key::display(&nk), a.label),
        }));
        targets.push(bound(&b));
        citations.push(GlobalCitation {
            start: a.start,
            end: b.end,
            targets,
        });
    }

    for r in &case_rows {
        let start: i32 = r.get(0);
        let end: i32 = r.get(1);
        let target_pid: String = r.get(2);
        let code: Option<String> = r.get(3);
        let date: Option<String> = r.get(4);
        let dockets: Option<Vec<String>> = r.get(5);
        let mut label = code
            .as_deref()
            .and_then(|c| refs.jurisdiction(c))
            .map(|j| j.label.clone())
            .unwrap_or_else(|| "Décision".to_string());
        if let Some(d) = date {
            label.push_str(&format!(", {d}"));
        }
        if let Some(n) = dockets.as_deref().and_then(|d| d.first()) {
            label.push_str(&format!(", n° {n}"));
        }
        citations.push(GlobalCitation {
            start: start.max(0) as usize,
            end: end.max(0) as usize,
            targets: vec![CitationTarget {
                href: Some(format!("/decision/{target_pid}")),
                label,
            }],
        });
    }
    citations.sort_by_key(|c| c.start);

    let raw_refs: Vec<RawLegalRef> = ref_rows
        .iter()
        .map(|r| {
            let instrument: String = r.get(0);
            let slug: Option<String> = r.get(1);
            let text_uid: String = r.get(2);
            let mut num_keys: Vec<String> = r.get(3);
            if let Some(members) = range_members.get(&text_uid) {
                num_keys.extend(members.iter().cloned());
                num_keys.sort();
                num_keys.dedup();
            }
            let articles: Vec<(String, Option<String>)> = num_keys
                .into_iter()
                .map(|k| {
                    let key = lj_core::article_key::article_key(&k);
                    (lj_core::article_key::display(&key), Some(key))
                })
                .collect();
            (instrument, slug, articles)
        })
        .collect();

    // Chronologie de l'affaire : décisions atteignables par les liens
    // appel/pourvoi/renvoi résolus, traversés dans les deux sens. Profondeur bornée
    // à 8 ; l'UNION coupe les cycles.
    let chrono_rows = conn
        .query(
            "
            WITH RECURSIVE chain(id, depth) AS (
                SELECT $1::bigint, 0
                UNION
                SELECT CASE WHEN dl.decision_id = c.id THEN dl.target_decision_id
                            ELSE dl.decision_id END,
                       c.depth + 1
                FROM chain c
                JOIN decision_links dl
                  ON dl.target_decision_id IS NOT NULL
                 AND (dl.decision_id = c.id OR dl.target_decision_id = c.id)
                WHERE c.depth < 8
            )
            SELECT d.public_id,
                   d.jurisdiction_code,
                   d.jurisdiction_type,
                   d.date_lecture::text,
                   d.id = $1 AS is_current,
                   d.id,
                   d.solution_uid,
                   d.docket_numbers
            FROM decisions d
            JOIN (SELECT DISTINCT id FROM chain) c ON c.id = d.id
            WHERE d.deleted_at IS NULL
            ORDER BY d.date_lecture DESC NULLS LAST, d.public_id
            ",
            &[&decision_id],
        )
        .await?;

    let chain_ids: Vec<i64> = chrono_rows.iter().map(|r| r.get::<_, i64>(5)).collect();
    let chrono_edges = conn
        .query(
            "
            SELECT s.public_id, t.public_id, dl.target_ref, dl.link_type
            FROM decision_links dl
            JOIN decisions s ON s.id = dl.decision_id
            LEFT JOIN decisions t ON t.id = dl.target_decision_id
            WHERE dl.decision_id = ANY($1)
              AND (dl.target_decision_id = ANY($1) OR dl.target_decision_id IS NULL)
            ",
            &[&chain_ids],
        )
        .await?;

    let (renvoyants, (citantes_total, citantes)) = {
        let repo = lj_store::repository::DecisionRepository::new(&conn);
        (
            repo.renvoyants(decision_id, RENVOYANTS_LIMIT).await?,
            repo.decisions_citing(decision_id, &chain_ids, CITANTES_LIMIT)
                .await?,
        )
    };

    // La connexion est rendue au pool avant le parse offloadé, qui ne touche plus
    // la DB.
    drop(conn);

    let chronology = chronology(&refs, &chrono_rows, &chrono_edges);

    // `source_fields` est un JSONB hétérogène par source : forme inattendue ⇒
    // champ vide, jamais d'erreur.
    let (themes, nac) = match source_fields.as_ref() {
        Some(sf) => (project_themes(sf), project_nac(sf)),
        None => (Vec::new(), None),
    };

    let official_url =
        source
            .as_deref()
            .zip(source_uid.as_deref())
            .and_then(|(source, source_uid)| {
                let field = |path: [&str; 2]| {
                    source_fields
                        .as_ref()
                        .and_then(|f| f.get(path[0]))
                        .and_then(|f| f.get(path[1]))
                        .and_then(serde_json::Value::as_str)
                };
                let top = |key: &str| {
                    source_fields
                        .as_ref()
                        .and_then(|f| f.get(key))
                        .and_then(serde_json::Value::as_str)
                };
                lj_core::official_url::official_url(&lj_core::official_url::SourceRef {
                    source,
                    source_uid,
                    court_code: field(["Dossier", "Code_Juridiction"]),
                    published_url: field(["META_JURI_CONSTIT", "URL_CC"])
                        .or_else(|| top("fiche_url")),
                    ariane_ref: top("decision_date").zip(
                        source_fields
                            .as_ref()
                            .and_then(|f| f.get("numbers"))
                            .and_then(|n| n.get(0))
                            .and_then(serde_json::Value::as_str),
                    ),
                })
            });

    // Reconstruction `(full_text, source_fields)` → `Decision` puis dérivation
    // paragraphes/sections : CPU-bloquant, donc offloadé sur `spawn_blocking`.
    let (paragraphs, paragraph_spans, sections, source_xml) =
        if let (Some(full_text), Some(source_fields)) = (full_text, source_fields) {
            let pid = public_id.to_string();
            tokio::task::spawn_blocking(move || -> ParsedPayload {
                let decision = Decision::from_source_fields(&full_text, &source_fields, &pid);
                let mut paragraphs = decision_paragraphs(&decision);
                let ranges = paragraph_global_ranges(&decision.texte_integral_clean, &paragraphs);
                let mut sections =
                    sections_from_decision(&decision, &paragraphs, &ranges, &citations);
                // Spans alignés sur le corps plat (repli front sans sections). Les offsets
                // sont en codepoints sur le texte original, et truecase préserve la
                // longueur en codepoints.
                let flat_spans = flat_paragraph_spans(&ranges, &citations);
                // Décisions intégralement en MAJUSCULES : recasse déterministe pour
                // l'affichage seulement, appliquée APRÈS l'assignation des sections, qui
                // matche les paragraphes par offsets sur le texte source.
                if truecase::is_caps_lock(&decision.texte_integral_clean) {
                    for p in &mut paragraphs {
                        *p = truecase::truecase(p);
                    }
                    if let Some(secs) = sections.as_mut() {
                        for section in secs.iter_mut() {
                            for p in &mut section.paragraphs {
                                *p = truecase::truecase(p);
                            }
                        }
                    }
                }
                (
                    paragraphs,
                    flat_spans,
                    sections,
                    Some(decision_source_meta(&decision)),
                )
            })
            .await
            .map_err(|e| ApiError::Internal(format!("payload parse task: {e}")))?
        } else {
            (Vec::new(), Vec::new(), None, None)
        };

    let legal_references = parse_legal_refs(&raw_refs);

    let docket_numbers = docket_numbers_raw.filter(|d| !d.is_empty());

    // Siège recomposé depuis les axes structurés, même composition que
    // `search_title` à l'ingest.
    let jur_display = crate::titles::decision_jurisdiction(
        refs.jurisdiction_type_label(&jur_type_raw)
            .unwrap_or(&jur_type_raw),
        jurisdiction_name.as_deref(),
    );
    let chamber_label = seat_stored.as_ref().and_then(lj_core::chamber::Seat::label);
    let seat = crate::titles::decision_seat(
        &jur_display,
        chamber_label.as_deref(),
        formation_uid.as_deref(),
        office_uid.as_deref(),
    );
    let title = lj_core::titles::decision_title(
        &jur_display,
        seat.as_deref(),
        date_lecture.as_deref(),
        case_name.as_deref(),
        docket_numbers
            .as_deref()
            .and_then(|d| d.first())
            .map(String::as_str),
    );

    let seat_path = crate::titles::seat_path_tag(&seat_paths);

    Ok(DecisionDetail {
        id,
        jurisdiction_type: jur_type,
        title,
        case_name,
        paragraphs,
        paragraph_spans,
        sections,
        summary,
        jurisdiction_code,
        jurisdiction_name,
        date_lecture,
        solution: opt_tag(&solution_uid, &refs),
        procedure: opt_tag(&procedure_uid, &refs),
        office: opt_tag(&office_uid, &refs),
        legal_domain: opt_tag(&legal_domain_uid, &refs),
        publication_codes,
        date_audience,
        docket_numbers,
        seat,
        seat_path,
        legal_references,
        source_xml,
        themes,
        nac,
        ecli,
        source,
        official_url,
        chronology,
        commentaires: {
            let mut c = ariane_bundle
                .as_ref()
                .map(commentaires_from_bundle)
                .unwrap_or_default();
            if let Some(files) = judilibre_files.as_ref() {
                c.extend(notes_from_judilibre_files(files));
            }
            if let Some(notes) = web_notes.as_ref() {
                c.extend(notes_from_web_bundle(notes));
            }
            c
        },
        renvoyants: renvoyants
            .into_iter()
            .map(|r| lj_dtos::Renvoyant {
                id: r.public_id,
                label: jurisdiction_label(
                    &refs,
                    r.jurisdiction_code.as_deref(),
                    &r.jurisdiction_type,
                ),
                date: r.date_lecture,
                docket_numbers: r.docket_numbers.filter(|d| !d.is_empty()),
            })
            .collect(),
        citantes: citantes
            .into_iter()
            .map(|r| crate::legi::citing_dto(r, &refs))
            .collect(),
        citantes_total: (citantes_total > CITANTES_LIMIT).then_some(citantes_total),
    })
}

/// Case chronology, most recent first: the decisions of the chain (`rows`) and,
/// for every link left pending, the step its key names without leading
/// anywhere. A lone step is no chronology.
fn chronology(
    refs: &Referential,
    rows: &[tokio_postgres::Row],
    edges: &[tokio_postgres::Row],
) -> Vec<lj_dtos::ChronologyEntry> {
    // Ordering and edge key: `public_id` of a step held by the corpus,
    // `target_ref` of a pending one.
    let mut steps: Vec<(String, lj_dtos::ChronologyEntry)> = rows
        .iter()
        .map(|r| {
            let public_id: String = r.get(0);
            let code: Option<String> = r.get(1);
            let jt: String = r.get(2);
            let solution_uid: Option<String> = r.get(6);
            (
                public_id.clone(),
                lj_dtos::ChronologyEntry {
                    id: Some(public_id),
                    label: jurisdiction_label(refs, code.as_deref(), &jt),
                    date: r.get(3),
                    current: r.get(4),
                    solution: solution_uid.as_deref().map(|u| refs.tag(u).key),
                    docket_numbers: r.get(7),
                    link: None,
                },
            )
        })
        .collect();

    let mut seen: HashSet<(String, Option<String>)> = steps
        .iter()
        .map(|(_, e)| (e.label.clone(), e.date.clone()))
        .collect();
    let mut links: HashMap<(String, String), String> = HashMap::new();
    for row in edges {
        let source: String = row.get(0);
        let target: Option<String> = row.get(1);
        let target_ref: String = row.get(2);
        let link_type: String = row.get(3);
        let Some(target) = target else {
            let Some(step) = crate::chronology::pending_step(&target_ref, refs) else {
                continue;
            };
            if seen.insert((step.label.clone(), Some(step.date.clone()))) {
                steps.push((
                    target_ref.clone(),
                    lj_dtos::ChronologyEntry {
                        id: None,
                        label: step.label,
                        date: Some(step.date),
                        current: false,
                        solution: None,
                        docket_numbers: step.docket.map(|d| vec![d]),
                        link: None,
                    },
                ));
            }
            links.insert((source, target_ref), link_type);
            continue;
        };
        links.insert((source, target), link_type);
    }

    if steps.len() < 2 {
        return Vec::new();
    }
    steps.sort_by(|a, b| b.1.date.cmp(&a.1.date).then_with(|| a.0.cmp(&b.0)));
    // A link reads from the more recent step to the decision it attacks.
    for i in 0..steps.len() - 1 {
        steps[i].1.link = links
            .get(&(steps[i].0.clone(), steps[i + 1].0.clone()))
            .cloned();
    }
    steps.into_iter().map(|(_, e)| e).collect()
}

/// Nom de la cour, repli sur le libellé du type de juridiction.
fn jurisdiction_label(refs: &Referential, code: Option<&str>, jur_type: &str) -> String {
    code.and_then(|c| refs.jurisdiction(c))
        .map(|j| j.label.clone())
        .unwrap_or_else(|| {
            refs.jurisdiction_type_label(jur_type)
                .unwrap_or(jur_type)
                .to_string()
        })
}

/// Commentaires doctrine web (`source_fields.commentaires[]` des fournisseurs
/// autres qu'ArianeWeb) → DTO. Entrées `note` auto-suffisantes : le lien est
/// stocké tel quel.
fn notes_from_web_bundle(notes: &serde_json::Value) -> Vec<lj_dtos::Commentaire> {
    notes
        .as_array()
        .map(|arr| {
            arr.iter()
                .filter(|c| c["kind"].as_str() == Some("note") && c["url"].is_string())
                .map(|c| lj_dtos::Commentaire {
                    kind: "note".to_string(),
                    author: c["author"].as_str().map(str::to_string),
                    date: c["date"].as_str().map(str::to_string),
                    body: None,
                    title: c["title"].as_str().map(str::to_string),
                    publisher: c["publisher"].as_str().map(str::to_string),
                    access: c["access"].as_str().map(str::to_string),
                    rubriques: Vec::new(),
                    renvois: Vec::new(),
                    url: c["url"].as_str().map(str::to_string),
                })
                .collect()
        })
        .unwrap_or_default()
}

/// Libellé public d'un type de document lié Judilibre (taxonomie `filetype`).
/// `None` = type non doctrinal (graphiques, décision annotée) → écarté.
fn judilibre_filetype_label(t: &str) -> Option<&'static str> {
    Some(match t {
        "prep_rapp" => "Rapport du conseiller",
        "prep_raco" => "Rapport complémentaire du conseiller",
        "prep_avpg" => "Avis du procureur général",
        "prep_avis" => "Avis de l'avocat général",
        "prep_oral" => "Avis oral de l'avocat général",
        "prep_avco" => "Avis complémentaire de l'avocat général",
        "comm_comm" => "Communiqué",
        "comm_note" => "Note explicative",
        "comm_nora" => "Notice au rapport annuel",
        "comm_lett" => "Lettre de chambre",
        "comm_trad" => "Arrêt traduit",
        _ => return None,
    })
}

/// Documents liés Judilibre (`files[]`) → commentaires `note` : rapports, avis,
/// communiqués, notes explicatives. Lien direct vers le PDF public (`rawUrl`).
/// Les graphiques et la décision annotée (`datt_*`) sont écartés.
fn notes_from_judilibre_files(files: &serde_json::Value) -> Vec<lj_dtos::Commentaire> {
    files
        .as_array()
        .map(|arr| {
            arr.iter()
                .filter_map(|f| {
                    let label = judilibre_filetype_label(f["type"].as_str()?)?;
                    let url = f["rawUrl"].as_str()?.to_string();
                    Some(lj_dtos::Commentaire {
                        kind: "note".to_string(),
                        author: None,
                        date: f["date"].as_str().map(str::to_string),
                        body: None,
                        title: Some(label.to_string()),
                        publisher: Some("Cour de cassation".to_string()),
                        access: None,
                        rubriques: Vec::new(),
                        renvois: Vec::new(),
                        url: Some(url),
                    })
                })
                .collect()
        })
        .unwrap_or_default()
}

/// Bundle `commentaires[]` ArianeWeb → DTO. Les analyses se déplient sur place ;
/// l'entrée `conclusions` (existence seule en base) devient une ligne-lien
/// composée ici — seul endroit à corriger si le Conseil d'État change son schéma
/// d'URL.
fn commentaires_from_bundle(bundle: &serde_json::Value) -> Vec<lj_dtos::Commentaire> {
    let dossier = bundle["dossier"].as_str();
    let date = bundle["date_lecture"].as_str();
    let str_vec = |v: &serde_json::Value| -> Vec<String> {
        v.as_array()
            .map(|a| {
                a.iter()
                    .filter_map(|s| s.as_str().map(str::to_string))
                    .collect()
            })
            .unwrap_or_default()
    };
    bundle["commentaires"]
        .as_array()
        .map(|arr| {
            arr.iter()
                .filter_map(|c| match c["kind"].as_str()? {
                    "analyse" => Some(lj_dtos::Commentaire {
                        kind: "analyse".to_string(),
                        author: c["author"].as_str().map(str::to_string),
                        date: c["date"].as_str().map(str::to_string),
                        body: c["body"].as_str().map(str::to_string),
                        title: None,
                        publisher: None,
                        access: None,
                        rubriques: str_vec(&c["meta"]["rubriques"]),
                        renvois: str_vec(&c["meta"]["renvois"]),
                        url: None,
                    }),
                    "conclusions" => Some(lj_dtos::Commentaire {
                        kind: "conclusions".to_string(),
                        author: None,
                        date: date.map(str::to_string),
                        body: None,
                        title: None,
                        publisher: None,
                        access: None,
                        rubriques: Vec::new(),
                        renvois: Vec::new(),
                        url: Some(format!(
                            "https://www.conseil-etat.fr/fr/arianeweb/CRP/conclusion/{}/{}",
                            date?, dossier?
                        )),
                    }),
                    _ => None,
                })
                .collect()
        })
        .unwrap_or_default()
}

/// Prévisualisation légère d'une décision par `public_id` : identité + solution
/// + codes de publication + résumé, sans lire le corps.
#[instrument(skip(state), fields(db.system = "postgresql", public_id = %public_id))]
pub async fn decision_preview(state: &AppState, public_id: &str) -> Result<DecisionPreview> {
    let refs = referential(state).await?;
    let conn = state.pool.get().await?;

    let row = conn
        .query_opt(
            "
            SELECT
              d.public_id,
              d.jurisdiction_type,
              d.jurisdiction_code,
              d.date_lecture::text,
              d.docket_numbers,
              d.solution_uid,
              d.procedure_uid,
              d.publication_codes,
              d.summary,
              d.seat,
              d.formation_uid,
              d.office_uid
            FROM decisions d
            WHERE d.public_id = $1
            ",
            &[&public_id],
        )
        .await?;
    let row = row.ok_or(ApiError::NotFound)?;

    let id: String = row.get(0);
    let jur_type_raw: String = row.get(1);
    let jurisdiction_code: Option<String> = row.get(2);
    let date_lecture: Option<String> = row.get(3);
    let docket_numbers: Option<Vec<String>> = row.get(4);
    let solution_uid: Option<String> = row.get(5);
    let procedure_uid: Option<String> = row.get(6);
    let publication_codes: Vec<String> = row.get(7);
    let summary: Option<String> = row.get(8);
    let seat_stored: Option<lj_core::chamber::Seat> = row
        .get::<_, Option<tokio_postgres::types::Json<lj_core::chamber::Seat>>>(9)
        .map(|j| j.0);
    let formation_uid: Option<String> = row.get(10);
    let office_uid: Option<String> = row.get(11);

    let jurisdiction_name = jurisdiction_code
        .as_deref()
        .and_then(|c| refs.jurisdiction(c))
        .map(|j| j.label.clone());
    let docket_numbers = docket_numbers.filter(|d| !d.is_empty());
    let jur_display = crate::titles::decision_jurisdiction(
        refs.jurisdiction_type_label(&jur_type_raw)
            .unwrap_or(&jur_type_raw),
        jurisdiction_name.as_deref(),
    );
    let chamber_label = seat_stored.as_ref().and_then(lj_core::chamber::Seat::label);
    let seat = crate::titles::decision_seat(
        &jur_display,
        chamber_label.as_deref(),
        formation_uid.as_deref(),
        office_uid.as_deref(),
    );
    let title = lj_core::titles::decision_title(
        &jur_display,
        seat.as_deref(),
        date_lecture.as_deref(),
        None,
        docket_numbers
            .as_deref()
            .and_then(|d| d.first())
            .map(String::as_str),
    );

    Ok(DecisionPreview {
        id,
        title,
        solution: opt_tag(&solution_uid, &refs),
        procedure: opt_tag(&procedure_uid, &refs),
        publication_codes,
        summary,
    })
}

/// Décisions similaires en deux volets pour un `public_id` :
///
/// - **principe** (référence, similaires sur le fond) : décisions de portée
///   notable par trois signaux fusionnés — citations sortantes résolues
///   (`case_citation`), articles rares partagés pondérés IDF, KNN pré-filtré
///   portée notable.
/// - **espèce** (similaires en fait) : ANN top-k sur les embeddings des chunks
///   bord, en excluant les hits principe et la chronologie de l'affaire
///   (`decision_links`, déjà affichée sur la page).
///
/// Les trois jambes partent en parallèle sur des connexions distinctes du pool ;
/// `limit` s'applique à chaque volet.
#[instrument(skip(state), fields(db.system = "postgresql", public_id = %public_id))]
pub async fn similar_decisions(
    state: &AppState,
    public_id: &str,
    limit: u32,
) -> Result<SimilarDecisionsResponse> {
    let limit = limit as usize;

    let (source_id, meta) = similar_source_meta(state, public_id)
        .await?
        .ok_or(ApiError::NotFound)?;

    let legs = similar_legs(state, source_id, limit).await?;

    let abstained = similar_principe_gated(&meta);
    let principe_ids = if abstained {
        Vec::new()
    } else {
        assemble_principe(&legs.direct, &legs.idf, &legs.principe_knn, limit)
    };
    let excluded: HashSet<i64> = principe_ids
        .iter()
        .chain(legs.chronology.iter())
        .copied()
        .collect();
    let espece_ids: Vec<i64> = if similar_espece_gated(&meta) {
        Vec::new()
    } else {
        legs.espece_knn
            .into_iter()
            .filter(|id| !excluded.contains(id))
            .take(limit)
            .collect()
    };

    let mut by_id = hydrate_similar_hits(
        state,
        &principe_ids
            .iter()
            .chain(espece_ids.iter())
            .copied()
            .collect::<Vec<i64>>(),
    )
    .await?;
    let collect = |ids: &[i64], by_id: &mut HashMap<i64, SimilarDecisionHit>| {
        ids.iter().filter_map(|id| by_id.remove(id)).collect()
    };
    Ok(SimilarDecisionsResponse {
        decision_id: public_id.to_string(),
        principe: collect(&principe_ids, &mut by_id),
        espece: collect(&espece_ids, &mut by_id),
        abstained,
    })
}

/// Au-delà de cette taille, un rejet CC citant le 1014 est un arrêt mixte motivé
/// (moyens réels + un moyen 1014), pas un rejet non spécialement motivé.
const GATE_1014_MAX_CHARS: i32 = 3_500;
/// Terme d'inversion `lj_cit_terms` de l'art. 1014 du code de procédure
/// civile (rejet non spécialement motivé).
const CPC_1014_TERM: &str = "LEGITEXT000006070716|1014";

/// Métadonnées de la décision-source pilotant l'abstention des volets
/// similaires.
pub struct SimilarSourceMeta {
    pub jurisdiction_type: String,
    pub solution_uid: Option<String>,
    pub text_chars: i32,
    pub cites_1014: bool,
}

/// Volet principe muet : la source ne tranche aucune question de droit —
/// désistement, non-lieu à statuer, ou rejet CC non spécialement motivé
/// (art. 1014 CPC, texte court).
pub fn similar_principe_gated(meta: &SimilarSourceMeta) -> bool {
    match meta.solution_uid.as_deref() {
        Some("solution:DESISTEMENT") | Some("solution:NON_LIEU_A_STATUER") => true,
        Some("solution:REJET") => {
            meta.jurisdiction_type == "CC"
                && meta.cites_1014
                && meta.text_chars < GATE_1014_MAX_CHARS
        }
        _ => false,
    }
}

/// Volet espèce muet : les voisines d'un désistement sont des donné-acte en
/// série sans valeur d'usage. Les non-lieux gardent leur volet.
pub fn similar_espece_gated(meta: &SimilarSourceMeta) -> bool {
    meta.solution_uid.as_deref() == Some("solution:DESISTEMENT")
}

/// Résout une décision par `public_id` : id interne + métadonnées du gate.
pub async fn similar_source_meta(
    state: &AppState,
    public_id: &str,
) -> Result<Option<(i64, SimilarSourceMeta)>> {
    let conn = state.pool.get().await?;
    let row = conn
        .query_opt(
            "
            SELECT d.id, d.jurisdiction_type, d.solution_uid,
                   coalesce(length(d.full_text), 0),
                   EXISTS (
                     SELECT 1 FROM legal_citation lc
                     WHERE lc.decision_id = d.id
                       AND public.lj_cit_terms(lc.spans) @> ARRAY[$2::text]
                   )
            FROM decisions d WHERE d.public_id = $1
            ",
            &[&public_id, &CPC_1014_TERM],
        )
        .await?;
    Ok(row.map(|r| {
        (
            r.get(0),
            SimilarSourceMeta {
                jurisdiction_type: r.get(1),
                solution_uid: r.get(2),
                text_chars: r.get(3),
                cites_1014: r.get(4),
            },
        )
    }))
}

/// Jambes brutes des deux volets, avant assemblage et hydratation.
pub struct SimilarLegs {
    /// Cibles résolues des citations sortantes, portée notable.
    pub direct: Vec<i64>,
    /// Décisions notables citant les mêmes articles rares, rang IDF.
    pub idf: Vec<i64>,
    /// Chronologie `decision_links` de l'affaire (exclue du volet espèce).
    pub chronology: Vec<i64>,
    /// KNN pré-filtré portée notable.
    pub principe_knn: Vec<i64>,
    /// KNN générique sur-fetché (volet espèce, avant exclusions).
    pub espece_knn: Vec<i64>,
}

/// Calcule les cinq jambes en parallèle sur des connexions distinctes du pool.
pub async fn similar_legs(state: &AppState, source_id: i64, limit: usize) -> Result<SimilarLegs> {
    let (espece_knn, principe_knn, graph) = tokio::try_join!(
        espece_knn_leg(state, source_id, limit),
        principe_knn_leg(state, source_id, limit),
        graph_legs(state, source_id, limit),
    )?;
    Ok(SimilarLegs {
        direct: graph.direct,
        idf: graph.idf,
        chronology: graph.chronology,
        principe_knn,
        espece_knn,
    })
}

/// Jambe espèce : ANN top-k générique sur les embeddings des chunks bord
/// (premier + dernier, max-pool par décision), sur-fetchée pour absorber les
/// exclusions.
async fn espece_knn_leg(state: &AppState, source_id: i64, limit: usize) -> Result<Vec<i64>> {
    let outer_limit = (limit as i64) * ESPECE_OVERFETCH_FACTOR;
    let inner_limit = (limit as i64) * SIMILAR_INNER_LIMIT_FACTOR;
    let query = format!(
        "
        WITH source AS (
          SELECT embedding
          FROM (
            SELECT
              c.embedding,
              row_number() OVER (ORDER BY c.chunk_index) AS rn_first,
              row_number() OVER (ORDER BY c.chunk_index DESC) AS rn_last
            FROM decision_chunks c
            WHERE c.decision_id = $1
              AND c.embedding IS NOT NULL
          ) ordered
          WHERE rn_first = 1 OR rn_last = 1
        ),
        neighbors AS MATERIALIZED (
          SELECT
            cand.decision_id,
            1 - cand.distance AS score
          FROM source src
          JOIN LATERAL (
            SELECT
              c.decision_id,
              c.embedding <=> src.embedding AS distance
            FROM decision_chunks c
            WHERE c.embedding IS NOT NULL
              AND c.decision_id <> $1
            ORDER BY distance
            LIMIT {inner_limit}
          ) cand ON TRUE
        )
        SELECT n.decision_id
        FROM neighbors n
        GROUP BY n.decision_id
        ORDER BY MAX(n.score) DESC, n.decision_id
        LIMIT {outer_limit}
        ",
    );
    knn_query(state, &query, source_id, state.settings.vchord_probes).await
}

/// Jambe principe KNN : même ANN, pré-filtrée portée notable *dans* le scan —
/// le filtre join force vchordrq à continuer en ordre de distance jusqu'à
/// remplir le LIMIT.
async fn principe_knn_leg(state: &AppState, source_id: i64, limit: usize) -> Result<Vec<i64>> {
    let limit = limit as i64;
    let query = format!(
        "
        WITH source AS (
          SELECT embedding
          FROM (
            SELECT
              c.embedding,
              row_number() OVER (ORDER BY c.chunk_index) AS rn_first,
              row_number() OVER (ORDER BY c.chunk_index DESC) AS rn_last
            FROM decision_chunks c
            WHERE c.decision_id = $1
              AND c.embedding IS NOT NULL
          ) ordered
          WHERE rn_first = 1 OR rn_last = 1
        ),
        neighbors AS MATERIALIZED (
          SELECT
            cand.decision_id,
            1 - cand.distance AS score
          FROM source src
          JOIN LATERAL (
            SELECT
              c.decision_id,
              c.embedding <=> src.embedding AS distance
            FROM decision_chunks c
            JOIN decisions dn ON dn.id = c.decision_id
            WHERE c.embedding IS NOT NULL
              AND c.decision_id <> $1
              AND dn.publication_codes && '{{{notable}}}'::text[]
            ORDER BY distance
            LIMIT {limit}
          ) cand ON TRUE
        )
        SELECT n.decision_id
        FROM neighbors n
        GROUP BY n.decision_id
        ORDER BY MAX(n.score) DESC, n.decision_id
        LIMIT {limit}
        ",
        notable = NOTABLE_CODES.join(","),
    );
    knn_query(state, &query, source_id, PRINCIPE_KNN_PROBES).await
}

/// Exécute une requête ANN (`$1` = decision_id source, une colonne
/// `decision_id`) sous `SET LOCAL vchordrq.probes`.
async fn knn_query(state: &AppState, query: &str, source_id: i64, probes: u32) -> Result<Vec<i64>> {
    let mut conn = state.pool.get().await?;
    let tx = conn.transaction().await?;
    tx.batch_execute(&format!("SET LOCAL vchordrq.probes = {probes}"))
        .await?;
    let rows = tx.query(query, &[&source_id]).await?;
    tx.commit().await?;
    Ok(rows.iter().map(|r| r.get(0)).collect())
}

/// Signaux du graphe de citations pour le volet principe, plus la chronologie
/// de l'affaire à exclure du volet espèce.
struct GraphLegs {
    /// Cibles résolues des citations sortantes, portée notable — majeures
    /// d'abord, puis les plus récentes.
    direct: Vec<i64>,
    /// Décisions notables citant les mêmes articles rares, rang IDF.
    idf: Vec<i64>,
    /// Décisions de la chronologie `decision_links`.
    chronology: Vec<i64>,
}

async fn graph_legs(state: &AppState, source_id: i64, limit: usize) -> Result<GraphLegs> {
    let limit = limit as i64;
    let notable: Vec<&str> = NOTABLE_CODES.to_vec();
    let majeure = vec!["r", "A"];
    let conn = state.pool.get().await?;

    let direct_rows = conn
        .query(
            "
            SELECT t.id
            FROM case_citation cc
            JOIN decisions t ON t.id = cc.target_decision_id
            WHERE cc.decision_id = $1
              AND t.publication_codes && $2
            GROUP BY t.id
            ORDER BY bool_or(t.publication_codes && $3) DESC,
                     MAX(t.date_lecture) DESC NULLS LAST, t.id
            LIMIT $4
            ",
            &[&source_id, &notable, &majeure, &limit],
        )
        .await?;

    // Articles rares partagés : termes article de la source (`text_uid|num_key`),
    // gardés sous le cap de rareté, inversés par le GIN `legal_citation_terms_idx`
    // vers les décisions notables, score Σ ln(N/df) avec N = estimation planner.
    // Codes inlinés, jamais liés : `idx_decisions_notable` est partiel, et d'un
    // paramètre le planificateur ne prouve pas l'implication sur un plan
    // générique. Mesuré : 607 ms littéral contre 1 541 ms lié.
    let notable_sql = NOTABLE_CODES.map(|code| format!("'{code}'")).join(", ");
    let idf_query = format!(
        "
        WITH terms AS (
          SELECT DISTINCT t
          FROM legal_citation lc, unnest(public.lj_cit_terms(lc.spans)) AS t
          WHERE lc.decision_id = $1 AND position('|' in t) > 0
        ),
        rare AS (
          SELECT t.t, s.decision_count
          FROM terms t
          JOIN citing_decision_counts s ON s.cited_term = t.t
          WHERE s.decision_count < {IDF_RARE_DF_CAP}
          ORDER BY s.decision_count ASC
          LIMIT {IDF_MAX_RARE_TERMS}
        )
        SELECT lc2.decision_id
        FROM rare r
        JOIN legal_citation lc2 ON public.lj_cit_terms(lc2.spans) @> ARRAY[r.t]
        JOIN decisions d2 ON d2.id = lc2.decision_id
        WHERE d2.publication_codes && ARRAY[{notable_sql}]::text[]
          AND lc2.decision_id <> $1
        GROUP BY lc2.decision_id
        ORDER BY sum(ln(
                     (SELECT greatest(reltuples, 1)::float8 FROM pg_class
                      WHERE oid = 'decisions'::regclass)
                     / r.decision_count::float8
                 )) DESC,
                 lc2.decision_id
        LIMIT $2
        ",
    );
    let idf_rows = conn.query(&idf_query, &[&source_id, &limit]).await?;

    let chrono_rows = conn
        .query(
            "
            WITH RECURSIVE chain(id, depth) AS (
                SELECT $1::bigint, 0
                UNION
                SELECT CASE WHEN dl.decision_id = c.id THEN dl.target_decision_id
                            ELSE dl.decision_id END,
                       c.depth + 1
                FROM chain c
                JOIN decision_links dl
                  ON dl.target_decision_id IS NOT NULL
                 AND (dl.decision_id = c.id OR dl.target_decision_id = c.id)
                WHERE c.depth < 8
            )
            SELECT DISTINCT id FROM chain WHERE id <> $1
            ",
            &[&source_id],
        )
        .await?;

    Ok(GraphLegs {
        direct: direct_rows.iter().map(|r| r.get(0)).collect(),
        idf: idf_rows.iter().map(|r| r.get(0)).collect(),
        chronology: chrono_rows.iter().map(|r| r.get(0)).collect(),
    })
}

/// Assemble le volet principe : citations directes d'abord, puis les hits en
/// accord IDF ∩ KNN, puis entrelacement alterné IDF/KNN.
pub fn assemble_principe(direct: &[i64], idf: &[i64], knn: &[i64], limit: usize) -> Vec<i64> {
    let knn_set: HashSet<i64> = knn.iter().copied().collect();
    let accord = idf.iter().copied().filter(|id| knn_set.contains(id));

    let mut interleaved = Vec::with_capacity(idf.len() + knn.len());
    let (mut it_idf, mut it_knn) = (idf.iter().copied(), knn.iter().copied());
    loop {
        let (a, b) = (it_idf.next(), it_knn.next());
        if a.is_none() && b.is_none() {
            break;
        }
        interleaved.extend(a);
        interleaved.extend(b);
    }

    let mut seen = HashSet::new();
    direct
        .iter()
        .copied()
        .chain(accord)
        .chain(interleaved)
        .filter(|id| seen.insert(*id))
        .take(limit)
        .collect()
}

/// Hydrate les cartes des deux volets en une requête, indexées par id interne ;
/// l'appelant rétablit l'ordre d'assemblage.
async fn hydrate_similar_hits(
    state: &AppState,
    ids: &[i64],
) -> Result<HashMap<i64, SimilarDecisionHit>> {
    if ids.is_empty() {
        return Ok(HashMap::new());
    }
    let conn = state.pool.get().await?;
    let rows = conn
        .query(
            "
            SELECT
              d.id,
              d.public_id,
              d.jurisdiction_type,
              d.jurisdiction_code,
              d.date_lecture::text,
              d.docket_numbers,
              d.solution_uid,
              d.procedure_uid,
              d.office_uid,
              d.publication_codes,
              d.summary
            FROM decisions d
            WHERE d.id = ANY($1)
            ",
            &[&ids],
        )
        .await?;
    drop(conn);

    let refs = referential(state).await?;
    let mut hits = HashMap::with_capacity(rows.len());
    for row in &rows {
        let internal_id: i64 = row.get(0);
        let id: String = row.get(1);
        let jur_type_raw: String = row.get(2);
        let jurisdiction_code: Option<String> = row.get(3);
        let date_lecture: Option<String> = row.get(4);
        let docket_numbers: Option<Vec<String>> = row.get(5);
        let docket_numbers = docket_numbers.filter(|d| !d.is_empty());
        let solution_uid: Option<String> = row.get(6);
        let procedure_uid: Option<String> = row.get(7);
        let office_uid: Option<String> = row.get(8);
        let publication_codes: Option<Vec<String>> = row.get(9);
        let summary: Option<String> = row.get(10);

        hits.insert(
            internal_id,
            SimilarDecisionHit {
                id,
                jurisdiction_type: parse_enum_str(&jur_type_raw).unwrap_or(JurisdictionType::Ta),
                jurisdiction_name: jurisdiction_code
                    .as_deref()
                    .and_then(|c| refs.jurisdiction(c))
                    .map(|j| j.label.clone()),
                date_lecture,
                docket_numbers,
                solution: opt_tag(&solution_uid, &refs),
                procedure: opt_tag(&procedure_uid, &refs),
                office: opt_tag(&office_uid, &refs),
                publication_codes: publication_codes.unwrap_or_default(),
                summary,
            },
        );
    }
    Ok(hits)
}

/// Désérialise une valeur d'enum sérialisée (SCREAMING_SNAKE) en variante Rust.
fn parse_enum_str<T: for<'de> serde::Deserialize<'de>>(code: &str) -> Option<T> {
    serde_json::from_value(serde_json::Value::String(code.to_string())).ok()
}

#[cfg(test)]
mod tests {
    use super::*;

    #[test]
    fn assemble_principe_direct_puis_accord_puis_entrelacement() {
        let out = assemble_principe(&[1], &[2, 3, 4], &[3, 5, 6], 6);
        assert_eq!(out, vec![1, 3, 2, 5, 4, 6]);
    }

    #[test]
    fn assemble_principe_cap_et_dedup_direct() {
        let out = assemble_principe(&[2], &[2, 3], &[4, 5], 3);
        assert_eq!(out, vec![2, 4, 3]);
    }

    fn gate_meta(
        jt: &str,
        solution: Option<&str>,
        chars: i32,
        cites_1014: bool,
    ) -> SimilarSourceMeta {
        SimilarSourceMeta {
            jurisdiction_type: jt.to_string(),
            solution_uid: solution.map(str::to_string),
            text_chars: chars,
            cites_1014,
        }
    }

    #[test]
    fn gate_desistement_coupe_les_deux_volets() {
        let m = gate_meta("TA", Some("solution:DESISTEMENT"), 2_500, false);
        assert!(similar_principe_gated(&m));
        assert!(similar_espece_gated(&m));
    }

    #[test]
    fn gate_non_lieu_coupe_le_principe_seul() {
        let m = gate_meta("TA", Some("solution:NON_LIEU_A_STATUER"), 2_500, false);
        assert!(similar_principe_gated(&m));
        assert!(!similar_espece_gated(&m));
    }

    #[test]
    fn gate_rejet_1014_court_cc_seulement() {
        let m = gate_meta("CC", Some("solution:REJET"), 2_406, true);
        assert!(similar_principe_gated(&m));
        assert!(!similar_principe_gated(&gate_meta(
            "CC",
            Some("solution:REJET"),
            8_249,
            true
        )));
        assert!(!similar_principe_gated(&gate_meta(
            "TA",
            Some("solution:REJET"),
            1_964,
            false
        )));
        assert!(!similar_principe_gated(&gate_meta(
            "CE", None, 2_047, false
        )));
    }

    #[test]
    fn assemble_principe_jambes_vides() {
        assert_eq!(assemble_principe(&[], &[], &[7, 8], 4), vec![7, 8]);
        assert!(assemble_principe(&[], &[], &[], 4).is_empty());
    }

    fn raw_ref(instrument: &str, slug: Option<&str>, articles: &[&str]) -> RawLegalRef {
        (
            instrument.to_string(),
            slug.map(str::to_string),
            articles
                .iter()
                .map(|a| (a.to_string(), Some(a.to_string())))
                .collect(),
        )
    }

    #[test]
    fn parse_legal_refs_keeps_instrument_without_articles() {
        let raw = vec![raw_ref("Code du travail", Some("code-du-travail"), &[])];
        let refs = parse_legal_refs(&raw).expect("ref conservée");
        assert_eq!(refs[0].instrument, "Code du travail");
        assert!(refs[0].articles.is_empty());
    }

    #[test]
    fn parse_legal_refs_empty_is_none() {
        assert!(parse_legal_refs(&[]).is_none());
    }

    #[test]
    fn parse_legal_refs_drops_unresolved_free_text() {
        let raw = vec![
            raw_ref("Règlement intérieur", None, &["12"]),
            raw_ref("Code civil", Some("code-civil"), &["1240"]),
        ];
        let refs = parse_legal_refs(&raw).expect("la ref résolue survit");
        assert_eq!(refs.len(), 1);
        assert_eq!(refs[0].instrument, "Code civil");
        let only_unresolved = vec![raw_ref("Règlement intérieur", None, &["12"])];
        assert!(parse_legal_refs(&only_unresolved).is_none());
    }

    #[test]
    fn paragraph_ranges_are_codepoints_and_never_rewind() {
        let clean = "Considérant café au lait\nRejet\nÀ nouveau é\nRejet";
        let decision = mk_decision(clean, Vec::new());
        let paragraphs = decision_paragraphs(&decision);
        let ranges = paragraph_global_ranges(&decision.texte_integral_clean, &paragraphs);
        assert_eq!(ranges.len(), 4);
        for (paragraph, &(start, end)) in paragraphs.iter().zip(&ranges) {
            let cut: String = clean.chars().skip(start).take(end - start).collect();
            assert_eq!(&cut, paragraph);
        }
        assert_ne!(ranges[1], ranges[3], "le second Rejet a sa propre plage");
    }

    #[test]
    fn section_labels_canonicalize_kinds() {
        assert_eq!(section_label("dispositif"), Some("Dispositif"));
        assert_eq!(section_label("visa"), Some("Visa"));
        assert_eq!(section_label("inconnu"), None);
    }

    // ── Spans de citation cliquables ──────────────────────────────────────────

    use lj_core::decision::DecisionSection as CoreSection;

    fn mk_decision(clean: &str, sections: Vec<CoreSection>) -> Decision {
        Decision {
            source_uid: String::new(),
            member_name: String::new(),
            ecli: None,
            jurisdiction_source_code: None,
            chamber: None,
            nac: None,
            jurisdiction_name: None,
            jurisdiction_type: None,
            jurisdiction_location: None,
            numero_dossier: None,
            numero_dossiers: None,
            numero_role: None,
            date_lecture: None,
            date_audience: None,
            date_mise_jour: None,
            formation: None,
            type_decision: None,
            type_recours: None,
            solution: None,
            publication_codes: Vec::new(),
            avocat_requerant: None,
            texte_integral_raw: clean.to_string(),
            texte_integral_clean: clean.to_string(),
            sections,
            metadata_header: String::new(),
            visa_trim: String::new(),
            themes: Vec::new(),
            attacked: None,
            parse_warnings: Vec::new(),
        }
    }

    fn cite(start: usize, end: usize, href: Option<&str>) -> GlobalCitation {
        GlobalCitation {
            start,
            end,
            targets: vec![CitationTarget {
                href: href.map(str::to_string),
                label: "Code civil 1240".to_string(),
            }],
        }
    }

    fn raw(start: usize, end: usize, text_uid: &str, num_key: Option<&str>) -> RawCite {
        RawCite {
            start,
            end,
            text_uid: text_uid.to_string(),
            slug: "code-de-la-route".to_string(),
            num_key: num_key.map(str::to_string),
            href: "/texte/code-de-la-route".to_string(),
            label: "Code de la route".to_string(),
            suivants: false,
        }
    }

    #[test]
    fn range_detection_bounds_du_meme_texte_separees_de_a() {
        let text: Vec<char> = "les articles L. 225-1 à L. 225-9 du code".chars().collect();
        assert_eq!(text[13..21].iter().collect::<String>(), "L. 225-1");
        assert_eq!(text[24..32].iter().collect::<String>(), "L. 225-9");
        let a = raw(13, 21, "LEGITEXT000006074228", Some("L. 225-1"));
        let b = raw(24, 32, "LEGITEXT000006074228", Some("L. 225-9"));
        assert!(is_article_range(&a, &b, &text));
        let autre = raw(24, 32, "LEGITEXT000006070933", Some("L. 225-9"));
        assert!(!is_article_range(&a, &autre, &text));
        let nue = raw(24, 32, "LEGITEXT000006074228", None);
        assert!(!is_article_range(&a, &nue, &text));
        let text_et: Vec<char> = "les articles L. 225-1 et L. 225-9 du code"
            .chars()
            .collect();
        assert!(!is_article_range(
            &a,
            &raw(25, 33, "LEGITEXT000006074228", Some("L. 225-9")),
            &text_et
        ));
    }

    #[test]
    fn range_stem_enumerable_ou_non() {
        assert_eq!(
            range_stem("L. 225-1", "L. 225-9"),
            Some(("L. 225".to_string(), 1, 9))
        );
        assert_eq!(range_stem("102", "108"), Some((String::new(), 102, 108)));
        assert_eq!(range_stem("L. 225-1", "L. 226-3"), None);
        assert_eq!(range_stem("50 sexies B", "H"), None);
        assert_eq!(range_stem("L. 225-9", "L. 225-1"), None);
        assert_eq!(range_stem("1", "300"), None);
        let (exact, like) = range_candidate_keys("L. 225", 1, 4);
        assert_eq!(exact, vec!["L. 225-2", "L. 225-3"]);
        assert_eq!(like, vec!["L. 225-1-%", "L. 225-2-%", "L. 225-3-%"]);
    }

    #[test]
    fn global_offset_maps_to_correct_paragraph_local_offset_with_multibyte() {
        let clean = "Considérant l'article 1240\nDécision rendue, voir 1241.";
        let p0_start = clean.chars().position(|c| c == 'C').unwrap();
        assert_eq!(p0_start, 0);
        let n_p0 = "Considérant l'article 1240".chars().count();
        let g_start = n_p0 - 4;
        let g_end = n_p0;

        let decision = mk_decision(clean, Vec::new());
        let ranges = paragraph_global_ranges(
            &decision.texte_integral_clean,
            &decision_paragraphs(&decision),
        );
        assert_eq!(ranges.len(), 2);
        let (p0s, p0e) = ranges[0];
        assert_eq!((p0s, p0e), (0, n_p0));
        let spans0 = spans_for_range(
            &[cite(g_start, g_end, Some("/texte/code-civil/1240"))],
            p0s,
            p0e,
        );
        assert_eq!(spans0.len(), 1);
        assert_eq!((spans0[0].start, spans0[0].end), (n_p0 - 4, n_p0));
        assert_eq!(
            clean.chars().skip(g_start).take(4).collect::<String>(),
            "1240"
        );
        let (p1s, p1e) = ranges[1];
        let spans1 = spans_for_range(&[cite(g_start, g_end, None)], p1s, p1e);
        assert!(spans1.is_empty());
    }

    #[test]
    fn overlapping_spans_merge_and_union_targets() {
        let short = cite(12, 20, Some("/texte/x/court"));
        let long = cite(10, 30, Some("/texte/x/long"));
        let spans = spans_for_range(&[short, long], 0, 40);
        assert_eq!(spans.len(), 1);
        assert_eq!((spans[0].start, spans[0].end), (10, 30));
        let hrefs: Vec<_> = spans[0].targets.iter().map(|t| t.href.as_deref()).collect();
        assert_eq!(hrefs, vec![Some("/texte/x/long"), Some("/texte/x/court")]);
    }

    #[test]
    fn coextensive_multi_article_yields_one_span_multi_target() {
        let mk = |href: &str, label: &str| GlobalCitation {
            start: 5,
            end: 40,
            targets: vec![CitationTarget {
                href: Some(href.to_string()),
                label: label.to_string(),
            }],
        };
        let cites = [
            mk("/texte/code-civil/1382", "1382"),
            mk("/texte/code-civil/1383", "1383"),
            mk("/texte/code-civil/1384", "1384"),
            mk("/texte/code-civil/1382", "1382"),
        ];
        let spans = spans_for_range(&cites, 0, 60);
        assert_eq!(spans.len(), 1);
        assert_eq!((spans[0].start, spans[0].end), (5, 40));
        assert_eq!(
            spans[0].targets.len(),
            3,
            "cibles distinctes, doublon fusionné"
        );
    }

    #[test]
    fn disjoint_spans_kept_and_sorted_by_start() {
        let a = cite(20, 24, Some("/texte/x/2"));
        let b = cite(5, 9, None);
        let spans = spans_for_range(&[a, b], 0, 40);
        assert_eq!(spans.len(), 2);
        assert_eq!((spans[0].start, spans[0].end), (5, 9));
        assert_eq!(spans[0].targets.len(), 1);
        assert!(spans[0].targets[0].href.is_none());
        assert_eq!((spans[1].start, spans[1].end), (20, 24));
        assert_eq!(spans[1].targets[0].href.as_deref(), Some("/texte/x/2"));
    }

    #[test]
    fn multi_occurrence_yields_one_span_per_mention() {
        let m1 = cite(3, 7, Some("/texte/x/9"));
        let m2 = cite(15, 19, Some("/texte/x/9"));
        let spans = spans_for_range(&[m1, m2], 0, 30);
        assert_eq!(spans.len(), 2);
        assert_eq!((spans[0].start, spans[0].end), (3, 7));
        assert_eq!((spans[1].start, spans[1].end), (15, 19));
    }

    #[test]
    fn span_outside_paragraph_is_ignored() {
        let spans = spans_for_range(&[cite(100, 110, Some("/texte/x/1"))], 0, 40);
        assert!(spans.is_empty());
        let spans = spans_for_range(&[cite(38, 45, Some("/texte/x/1"))], 0, 40);
        assert!(spans.is_empty());
    }
}

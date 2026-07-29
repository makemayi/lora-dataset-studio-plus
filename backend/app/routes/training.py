"""Training API: launch/continue/queue/stop a LoRA training run via ai-toolkit,
plus checkpoint listing/import/delete and Z-Image base-conversion prep.

No login - single local user (`cfg.LOCAL_USER`). Every route except
`/dataset/train/status` is gated on `capabilities.probe()['aitoolkit']['valid']`
(409 with a UI hint): `/train/status` must stay pollable even when
ai-toolkit isn't configured, so it degrades to `{'available': False}` instead.
"""
import os
import re
from datetime import datetime

from flask import Blueprint, current_app, request, jsonify

from .. import capabilities
from .. import config as cfg
from ..config import LOCAL_USER
from ..services import cloud_training as ct
from ..services import face_dataset_service as svc
from ..services import face_mask
from ..services import face_mask_preview as fmp
from ..models import FaceDatasetImage
from ..services import lora_training as lt
from ..services import zimage_convert as zc
from ..utils.comfyui import get_zimage_models, get_checkpoint_models
from ._common import _map_error

bp = Blueprint('training', __name__, url_prefix='/api')


def _require_aitoolkit():
    """None if ai-toolkit is usable, else the (body, status) 409 to return."""
    if not capabilities.probe()['aitoolkit']['valid']:
        return jsonify({'error': 'ai-toolkit is not configured',
                        'hint': 'Set its folder in Settings'}), 409
    return None


def _require_cloud():
    """None if cloud training is configured, else the (body, status) 409 to return."""
    if not capabilities.probe().get('cloud_training'):
        return jsonify({'error': 'Cloud training is not configured',
                        'hint': 'Add your vast.ai API key in Settings'}), 409
    return None


@bp.post('/dataset/<int:dataset_id>/train')
def dataset_train(dataset_id):
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    d = request.get_json(silent=True) or {}
    try:
        # steps optionnel : None → adaptatif. base_model='' → officiel ; sinon merge
        # (doit être converti d'abord). variant règle l'adapter de de-distillation.
        # base_model peut être un chemin ABSOLU (« Custom weights… », local-only).
        # vae_path/te_path = overrides SDXL uniquement (le service refuse en 400
        # pour toute autre famille). Présence-conditionnelle : absent → le service
        # garde la valeur persistée (sentinelle _PERSISTED), jamais un reset muet.
        kw = {}
        if 'vae_path' in d:
            kw['vae_path'] = d.get('vae_path')
        if 'te_path' in d:
            kw['te_path'] = d.get('te_path')
        res = lt.launch_training(LOCAL_USER, dataset_id, steps=d.get('steps'),
                                 base_model=d.get('base_model'),
                                 variant=d.get('variant', 'turbo'),
                                 train_type=d.get('train_type'),
                                 allow_caption_mismatch=bool(d.get('allow_caption_mismatch')),
                                 allow_uncaptioned=bool(d.get('allow_uncaptioned')),
                                 allow_caption_quality=bool(d.get('allow_caption_quality')),
                                 allow_unverified_weights=bool(d.get('allow_unverified_weights')),
                                 # « Continue anyway » du panneau de préparation : lève le
                                 # garde-fou plancher d'images (jamais une impossibilité physique).
                                 allow_not_ready=bool(d.get('allow_not_ready')),
                                 # Absent = read the dataset's stored setting
                                 # (persisted; it used to be a browser-only value).
                                 masked=d.get('masked'),
                                 # fresh=True : écarte le run existant (archivé, pas
                                 # détruit) → repart de zéro au lieu de l'auto-resume.
                                 fresh=bool(d.get('fresh')), **kw)
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **res})


@bp.post('/dataset/<int:dataset_id>/train/continue')
def dataset_train_continue(dataset_id):
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    d = request.get_json(silent=True) or {}
    # base_model/variant = base sélectionnée (absente → base persistée du run).
    kw = {'extra_steps': d.get('extra_steps', 1000)}
    if 'base_model' in d:
        kw['base_model'] = d.get('base_model')
    if d.get('variant'):
        kw['variant'] = d.get('variant')
    if d.get('train_type'):
        kw['train_type'] = d.get('train_type')
    # from_step = reprise depuis un checkpoint précis (défaut = dernier). overrides =
    # réglages sûrs (le service refuse toute clé hors liste → 400).
    if d.get('from_step') is not None:
        kw['from_step'] = d.get('from_step')
    if d.get('overrides') is not None:
        kw['overrides'] = d.get('overrides')
    kw['masked'] = d.get('masked')
    kw['allow_unverified_weights'] = bool(d.get('allow_unverified_weights'))
    kw['allow_caption_mismatch'] = bool(d.get('allow_caption_mismatch'))
    kw['allow_uncaptioned'] = bool(d.get('allow_uncaptioned'))
    kw['allow_caption_quality'] = bool(d.get('allow_caption_quality'))
    kw['allow_not_ready'] = bool(d.get('allow_not_ready'))
    try:
        res = lt.continue_training(LOCAL_USER, dataset_id, **kw)
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **res})


@bp.get('/dataset/train/status')
def dataset_train_status():
    # Le poll doit toujours répondre 200 (jamais d'erreur) : sans ai-toolkit
    # configuré, on renvoie juste 'indisponible' au lieu d'un 409 qui casserait
    # le polling UI.
    if not capabilities.probe()['aitoolkit']['valid']:
        return jsonify({'available': False})
    # Le poll fait avancer la file : fin du training courant → lancement du suivant.
    try:
        lt.process_training_queue()
    except Exception:
        pass
    return jsonify(lt.training_status(LOCAL_USER))


@bp.post('/dataset/<int:dataset_id>/train/enqueue')
def dataset_train_enqueue(dataset_id):
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    d = request.get_json(silent=True) or {}
    # base_model/variant = base CHOISIE pour le job en file (absente → persistée).
    kw = {'extra_steps': d.get('extra_steps'), 'masked': d.get('masked')}
    if 'base_model' in d:
        kw['base_model'] = d.get('base_model')
    if d.get('variant'):
        kw['variant'] = d.get('variant')
    if d.get('train_type'):
        kw['train_type'] = d.get('train_type')
    if d.get('allow_caption_mismatch'):
        kw['allow_caption_mismatch'] = True
    if d.get('allow_uncaptioned'):
        kw['allow_uncaptioned'] = True
    if d.get('allow_caption_quality'):
        kw['allow_caption_quality'] = True
    if d.get('allow_unverified_weights'):
        kw['allow_unverified_weights'] = True
    if d.get('allow_not_ready'):
        kw['allow_not_ready'] = True
    # SDXL custom overrides (service refuses them 400 for any other family).
    if 'vae_path' in d:
        kw['vae_path'] = d.get('vae_path')
    if 'te_path' in d:
        kw['te_path'] = d.get('te_path')
    # steps = cible absolue choisie côté UI (None → adaptatif). Forwarding conditionnel.
    if d.get('steps') is not None:
        kw['steps'] = d.get('steps')
    try:
        res = lt.enqueue_training(LOCAL_USER, dataset_id, **kw)
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **res})


@bp.post('/dataset/<int:dataset_id>/train/schedule')
def dataset_train_schedule(dataset_id):
    """Programme un entraînement (jour + heure locale). Contrairement à SRC, une
    échéance déjà PASSÉE est refusée (400) plutôt que dégradée en « dû
    immédiatement » : un `at` dans le passé est presque toujours une saisie
    erronée côté UI, pas une intention de lancer tout de suite."""
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    d = request.get_json(silent=True) or {}
    raw = str(d.get('at') or '').strip()   # datetime-local: "YYYY-MM-DDTHH:MM"
    try:
        at = datetime.fromisoformat(raw)
        # Normalize tz-aware to local naive for comparison
        if at.tzinfo is not None:
            at = at.astimezone().replace(tzinfo=None)
        if at <= datetime.now():
            return jsonify({'error': 'scheduled time is in the past'}), 400
    except (TypeError, ValueError):
        return jsonify({'error': 'invalid schedule time'}), 400
    kw = {'extra_steps': d.get('extra_steps'), 'not_before': at.isoformat(timespec='minutes'),
          'masked': d.get('masked')}
    if 'base_model' in d:
        kw['base_model'] = d.get('base_model')
    if d.get('variant'):
        kw['variant'] = d.get('variant')
    if d.get('train_type'):
        kw['train_type'] = d.get('train_type')
    if d.get('allow_caption_mismatch'):
        kw['allow_caption_mismatch'] = True
    if d.get('allow_uncaptioned'):
        kw['allow_uncaptioned'] = True
    if d.get('allow_caption_quality'):
        kw['allow_caption_quality'] = True
    if d.get('allow_unverified_weights'):
        kw['allow_unverified_weights'] = True
    if d.get('allow_not_ready'):
        kw['allow_not_ready'] = True
    if 'vae_path' in d:
        kw['vae_path'] = d.get('vae_path')
    if 'te_path' in d:
        kw['te_path'] = d.get('te_path')
    if d.get('steps') is not None:
        kw['steps'] = d.get('steps')
    try:
        res = lt.enqueue_training(LOCAL_USER, dataset_id, **kw)
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **res})


@bp.post('/dataset/<int:dataset_id>/train/dequeue')
def dataset_train_dequeue(dataset_id):
    gate = _require_aitoolkit()
    if gate:
        return gate
    # Ownership : on ne retire de la file que SES propres datasets (anti-IDOR).
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    n = lt.dequeue_training(dataset_id)
    return jsonify({'ok': True, 'removed': n})


@bp.post('/dataset/train/stop')
def dataset_train_stop():
    # Single-user app : pas de vérif d'ownership sur l'entraînement en cours.
    gate = _require_aitoolkit()
    if gate:
        return gate
    d = request.get_json(silent=True) or {}
    expected_dataset_id = d.get('dataset_id')
    expected_run_token = d.get('run_token')
    if (expected_dataset_id is None) != (expected_run_token is None):
        return jsonify({
            'ok': False,
            'error': 'dataset_id and run_token must be provided together',
        }), 400
    if expected_dataset_id is not None:
        try:
            expected_dataset_id = int(expected_dataset_id)
        except (TypeError, ValueError):
            return jsonify({'ok': False, 'error': 'invalid dataset id'}), 400
    if expected_run_token is not None:
        if not isinstance(expected_run_token, str) or not expected_run_token.strip():
            return jsonify({'ok': False, 'error': 'invalid run token'}), 400
        expected_run_token = expected_run_token.strip()
    # Preserve the original no-argument call for the dataset-manager button;
    # only the Runs hub opts into target-aware protection.
    stopped = (lt.stop_training()
               if expected_dataset_id is None and expected_run_token is None
               else lt.stop_training(
                   expected_dataset_id=expected_dataset_id,
                   expected_run_token=expected_run_token))
    if stopped is False:
        # The Runs hub polls every few seconds. Its card can therefore describe
        # run A just after A ended and queued run B started; never let that stale
        # button kill B. Older callers omit dataset_id and keep global semantics.
        return jsonify({
            'ok': False,
            'error': 'This local run is no longer active. The Runs page was refreshed.',
        }), 409
    return jsonify({'ok': True})


@bp.get('/dataset/<int:dataset_id>/train/checkpoints')
def dataset_train_checkpoints(dataset_id):
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    # base_model = base sélectionnée dans le dropdown (param absent → base persistée).
    bm = request.args.get('base_model')
    # train_type = famille sélectionnée dans le menu LORA TYPE (param absent →
    # famille persistée).
    fam = request.args.get('train_type') or None
    variant = request.args.get('variant') or None
    kw = {} if bm is None else {'base_model': bm}
    if fam:
        kw['family'] = fam
    if variant:
        kw['variant'] = variant
    from ..models import CloudTrainingRun
    from ..services import checkpoint_registry
    ds = svc.get_dataset(LOCAL_USER, dataset_id)
    fam_resolved = lt._train_type(ds, fam)
    # Retrofit for datasets trained BEFORE the provenance registry existed:
    # training evidence without records -> record the current state as the v1
    # baseline, so versioning covers the past, not only future runs. Runs
    # BEFORE list_checkpoints so the fresh baseline annotates this response.
    had_training = (bool(lt.list_checkpoints(LOCAL_USER, dataset_id, **kw))
                    or any((ct._run_family(r) or fam_resolved) == fam_resolved
                           for r in CloudTrainingRun.query
                           .filter_by(dataset_id=dataset_id).all()))
    checkpoint_registry.ensure_baseline(LOCAL_USER, dataset_id, fam_resolved,
                                        had_training)
    # Deployment stamp (testable + deployed_filename) on EVERY listed save, from
    # the same join the ◉ Graph pills use — this is what lets the panel show
    # "✓ Deployed + ⏏ Undeploy" in place of a misleading second "Import →", and
    # aim the undeploy at the right ComfyUI file. Local rows name their own run,
    # so they are grouped by run; a cloud group IS one run.
    local_cks = ct.annotate_deployed_by_run(
        dataset_id, fam_resolved, lt.list_checkpoints(LOCAL_USER, dataset_id, **kw))
    cloud_groups = ct.cloud_checkpoint_groups(dataset_id, fam_resolved, variant=variant)
    for _g in cloud_groups:
        ct.annotate_deployed_checkpoints(dataset_id, fam_resolved,
                                         _g.get('checkpoints') or [],
                                         run_tag=('cloud', _g.get('run_id')))
    return jsonify({'checkpoints': local_cks,
                    # cloud saves synced locally (incl. an ACTIVE run's latest)
                    # — separate field: the resume-or-fresh prompt reasons on
                    # LOCAL checkpoints only
                    'cloud_checkpoints': ct.annotate_deployed_by_run(
                        dataset_id, fam_resolved,
                        [dict(c, run_source='cloud') for c in ct.cloud_checkpoints(
                            dataset_id, fam_resolved, variant=variant)]),
                    # same saves grouped BY SOURCE RUN (id/status/gpu/cost/time)
                    # so the panel labels which run produced which epochs and
                    # deep-links each group back to its Runs row
                    'cloud_checkpoint_groups': cloud_groups,
                    'recommended_steps': lt.recommended_steps(
                        dataset_id, train_type=fam_resolved, variant=variant),
                    'recommended_steps_info': lt.recommended_steps_info(
                        dataset_id, train_type=fam_resolved, variant=variant),
                    'imported': lt.list_imported_checkpoints(LOCAL_USER, dataset_id, family=fam),
                    'disk_usage': lt.dataset_disk_usage(LOCAL_USER, dataset_id, **kw),
                    # provenance: latest registered dataset version vs the
                    # dataset's CURRENT state (drift warning in the panel)
                    'dataset_state': checkpoint_registry.dataset_state(
                        LOCAL_USER, dataset_id, fam_resolved)})


@bp.get('/dataset/<int:dataset_id>/train/progress')
def dataset_train_progress(dataset_id):
    """Live run view for the TrainingPanel: parsed log progress (step/total/loss/
    speed/eta + downsampled loss curve) and the sample previews ai-toolkit writes.
    Answers 200 with log_exists=false before the log shows up — pollable early."""
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    bm = request.args.get('base_model')
    fam = request.args.get('train_type') or None
    variant = request.args.get('variant') or None
    kw = {} if bm is None else {'base_model': bm}
    if fam:
        kw['family'] = fam
    if variant:
        kw['variant'] = variant
    try:
        return jsonify(lt.training_progress(LOCAL_USER, dataset_id, **kw))
    except Exception as e:
        return _map_error(e)


_SAMPLE_NAME_RE = re.compile(r'^[\w.-]+\.(?:jpg|jpeg|png|webp)$', re.IGNORECASE)


@bp.get('/dataset/<int:dataset_id>/train/sample/<filename>')
def dataset_train_sample(dataset_id, filename):
    """Serve one training sample image. Filename is whitelist-validated (no
    separators/traversal) and resolved strictly inside the run's samples dir."""
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    if not _SAMPLE_NAME_RE.match(filename) or filename != os.path.basename(filename):
        return jsonify({'error': 'invalid filename'}), 400
    bm = request.args.get('base_model')
    fam = request.args.get('train_type') or None
    variant = request.args.get('variant') or None
    kw = {} if bm is None else {'base_model': bm}
    if fam:
        kw['family'] = fam
    if variant:
        kw['variant'] = variant
    try:
        d = lt._samples_dir(LOCAL_USER, dataset_id, **kw)
    except Exception as e:
        return _map_error(e)
    path = os.path.join(d, filename)
    if not os.path.isfile(path):
        return jsonify({'error': 'not found'}), 404
    from flask import send_file
    return send_file(path, conditional=True)


@bp.get('/dataset/<int:dataset_id>/train/preflight')
def dataset_train_preflight(dataset_id):
    """Pre-launch sanity report (blockers + warnings): image floor per family,
    composition balance, caption quality, identity leaks, near-duplicates,
    untriaged images, VRAM. The TrainingPanel calls it before Train/Queue/
    Schedule and turns warnings into ONE confirm.

    `?lane=cloud` drops the rows that read THIS machine (GPU memory, torch build)
    — they describe hardware that will not run a cloud job. Absent or `local`
    returns the historical payload unchanged.

    `?masked=1|0` states whether the launch intends masked (person-mask) training,
    a client-side preference the server cannot read. Absent = not stated, and the
    person-mask readiness row is omitted."""
    # The gate follows the lane. A cloud-only install has no ai-toolkit, so the
    # historical _require_aitoolkit() would 409 exactly where these warnings matter
    # most (money is about to be spent) — and the caller treats a non-200 as "no
    # objection", which would have made the whole cloud preflight a silent no-op.
    lane = request.args.get('lane') or None
    raw_masked = request.args.get('masked')
    masked = None if raw_masked is None else raw_masked not in ('0', 'false', '')
    gate = _require_cloud() if lane == 'cloud' else _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    try:
        return jsonify({'ok': True, **lt.training_preflight(
            LOCAL_USER, dataset_id,
            train_type=request.args.get('train_type') or None,
            variant=request.args.get('variant') or None,
            lane=lane, masked=masked)})
    except Exception as e:
        return _map_error(e)


@bp.post('/dataset/<int:dataset_id>/train/best-epoch')
def dataset_train_best_epoch(dataset_id):
    """Score every training sample vs the reference (face similarity, CPU) and
    recommend the checkpoint closest to the best-scoring step. Synchronous —
    one insightface subprocess for the whole set (~seconds to ~1 min)."""
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    d = request.get_json(silent=True) or {}
    bm = d.get('base_model')
    fam = d.get('train_type') or None
    kw = {} if bm is None else {'base_model': bm}
    if fam:
        kw['family'] = fam
    if d.get('variant'):
        kw['variant'] = d.get('variant')
    try:
        return jsonify({'ok': True, **lt.score_checkpoint_samples(LOCAL_USER, dataset_id, **kw)})
    except Exception as e:
        return _map_error(e)


def _face_preview_kept(dataset_id):
    """The kept set as PLAIN data — {path: (image_id, filename)} — plus a
    fingerprint of it. Plain on purpose: the detection runs in a worker thread and
    ORM rows must not travel across the session that loaded them."""
    kept = (FaceDatasetImage.query
            .filter_by(dataset_id=dataset_id, status='keep')
            .filter(FaceDatasetImage.filename.isnot(None)).all())
    by_path, stamps = {}, []
    for img in kept:
        p = os.path.join(svc._dataset_dir(dataset_id), img.filename)
        try:
            st = os.stat(p)
        except OSError:
            continue        # deleted under us — not part of what would be trained
        by_path[p] = (img.id, img.filename)
        stamps.append((img.id, img.filename, st.st_size, st.st_mtime_ns))
    return by_path, fmp.fingerprint(stamps)


def _face_preview_payload(results, by_path, limit):
    """Fold a detection result map into what the panel draws.

    The SAMPLE is deliberately failure-first: images where no face was found are
    the instructive ones (profile, cropped, too small) — a preview of successes
    only would hide exactly what the user needs to see. `coverage` is computed
    over the WHOLE kept set regardless, because a partially masked set is the bad
    case."""
    missed = [p for p, r in results.items() if (r or {}).get('state') != 'masked']
    found = [p for p, r in results.items() if (r or {}).get('state') == 'masked']
    samples = [{'image_id': by_path[p][0], 'filename': by_path[p][1],
                'state': (results[p] or {}).get('state'),
                'boxes': (results[p] or {}).get('boxes') or []}
               for p in (missed + found)[:limit] if p in by_path]
    return {'samples': samples, 'coverage': face_mask.coverage_summary(results),
            'expand': face_mask.expand_factor()}


def _face_preview_guard(dataset_id, require_tool=True):
    """Shared gate. Returns an error response, or None."""
    ds = svc.get_dataset(LOCAL_USER, dataset_id)
    if not ds:
        return jsonify({'error': 'not found'}), 404
    if not svc.is_concept(ds):
        return jsonify({'ok': False, 'error': 'face masking is for concept datasets'}), 400
    if require_tool and not face_mask.is_available():
        # Degrade by SAYING SO, INSTANTLY. The option itself is disabled in the UI
        # on the same capability, so this is the belt to that brace — and an install
        # without face detection must hear it now, not after a timeout.
        return jsonify({'ok': False, 'error': 'face detection unavailable',
                        'reason': 'face_scoring'}), 409
    return None


@bp.post('/dataset/<int:dataset_id>/train/face-mask-preview')
def dataset_face_mask_preview(dataset_id):
    """START (or JOIN) the face detection behind the training panel's mask preview,
    so it can draw what face masking would cover before anything is trained.

    Detection only — no generation, no training, nothing written to disk.

    Asynchronous on purpose. A blocking request could show nothing while it ran
    (the InsightFace model load alone is tens of seconds before image 1) and could
    not be rejoined: leaving the page threw the pass away and coming back offered
    to start a second one. The job lives in face_mask_preview, so a second click —
    or a return to the page — joins the pass in flight instead of duplicating it.

    RAW boxes are returned, not grown ones: the expand factor is applied in the
    browser (utils/faceMaskBox.js mirrors infer/face_mask_infer.dilate_box), so
    dragging the slider redraws instantly instead of paying for another InsightFace
    pass. One pass, then the knob is free."""
    gate = _face_preview_guard(dataset_id)
    if gate:
        return gate
    limit = max(1, min(12, int((request.get_json(silent=True) or {}).get('limit') or 6)))
    by_path, fp = _face_preview_kept(dataset_id)
    if not by_path:
        # Nothing kept is a valid answer, not a job. Publish it so a return to the
        # page shows the same thing rather than an inviting button.
        fmp.set_result(dataset_id, _face_preview_payload({}, {}, limit), fp)
        return jsonify({'ok': True, 'started': False, **fmp.snapshot(dataset_id, fp)})

    paths = list(by_path)
    app = current_app._get_current_object()

    def _work(job):
        data = face_mask.detect_faces(
            paths, on_progress=lambda rec: fmp.progress(job, rec))
        if not data.get('ok'):
            # An operation that failed must LOOK failed. The reason travels all the
            # way to the panel instead of dying in a log line.
            fmp.fail(job, data.get('error') or 'face detection failed')
            return
        # Zero faces is a RESULT, not a failure: a concept dataset may legitimately
        # hold no people. It publishes like any other pass.
        fmp.set_result(dataset_id, _face_preview_payload(
            data.get('results') or {}, by_path, limit), fp)

    job, started = fmp.start(app, dataset_id, _work, total=len(paths), fp=fp)
    return jsonify({'ok': True, 'started': started, **fmp.snapshot(dataset_id, fp)}), 202


@bp.get('/dataset/<int:dataset_id>/train/face-mask-preview')
def dataset_face_mask_preview_status(dataset_id):
    """Rebind: the running pass (phase + i/M) and the last preview computed for
    this dataset. Called on mount and while polling, so leaving the page and
    coming back picks the pass back up instead of restarting it.

    `result.stale` is the honest half: the stored preview describes the kept set
    it was computed from, and if that set moved since, showing it as fresh would
    be worse than showing nothing."""
    gate = _face_preview_guard(dataset_id, require_tool=False)
    if gate:
        return gate
    _, fp = _face_preview_kept(dataset_id)
    return jsonify({'ok': True, 'available': face_mask.is_available(),
                    **fmp.snapshot(dataset_id, fp)})


@bp.get('/dataset/<int:dataset_id>/train/base-info')
def dataset_train_base_info(dataset_id):
    """Bases entraînables (officielle + merges Z-Image), base/variante choisies du
    dataset, et statut de conversion - pour le sélecteur du TrainingPanel."""
    gate = _require_aitoolkit()
    if gate:
        return gate
    ds = svc.get_dataset(LOCAL_USER, dataset_id)
    if not ds:
        return jsonify({'error': 'not found'}), 404
    bases = [{'value': '', 'label': 'Official - Z-Image-Turbo (recommended)'}]
    converted = {}
    for m in get_zimage_models():
        bases.append({'value': m, 'label': m.replace('\\', '/').split('/')[-1].rsplit('.', 1)[0]})
        converted[m] = zc.is_converted(m)
    # Bases SDXL = checkpoints ComfyUI existants (single-file, pas de conversion).
    # get_checkpoint_models() renvoie des DICTS {name, civitai_url, score} (pas des
    # strings comme get_zimage_models) → extraire 'name'.
    sdxl_bases = []
    for c in (get_checkpoint_models() or []):
        name = c['name'] if isinstance(c, dict) else c
        sdxl_bases.append({'value': name,
                           'label': name.replace('\\', '/').split('/')[-1].rsplit('.', 1)[0]})
    # Krea 2 : base officielle fixe (pas de checkpoint custom, pas de conversion) ; le
    # choix Raw/Turbo se fait via le sélecteur `variant`, pas ici → label neutre.
    krea_bases = [{'value': '', 'label': 'Official - Krea 2'}]
    # Flux : base officielle fixe (FLUX.1-dev, gated HF) — pas de checkpoint custom ni
    # de conversion. Entrée explicite pour que l'UI n'aille PAS retomber sur les bases
    # Z-Image (fallback `bases_by_type[type] || bases`) quand la famille est Flux.
    flux_bases = [{'value': '', 'label': 'Official - FLUX.1-dev'}]
    # FLUX.2 Klein : bases officielles fixes (gated HF) — le choix 4B/9B se fait via
    # le sélecteur `variant` (comme Raw/Turbo pour Krea), pas ici → label neutre.
    flux2klein_bases = [{'value': '', 'label': 'Official - FLUX.2 Klein'}]
    # Les listers de bases (get_checkpoint_models / get_zimage_models) résolvent le
    # dossier des modèles depuis comfyui.base_dir → vides tant qu'il n'est pas
    # configuré. On expose ce fait pour que l'UI dise « configure ComfyUI dans Setup »
    # au lieu d'un « No checkpoint found » aveugle (le vrai motif sur un clone neuf).
    models_dir = None
    try:
        models_dir = cfg.comfyui_dir('models')
    except Exception:
        models_dir = None
    comfyui_configured = bool(models_dir) and os.path.isdir(str(models_dir))
    # `base` must be what this run will ACTUALLY train on. train_base_model is a
    # single column shared by every family, so a dataset switched from Z-Image to
    # Krea 2 still carries the Z-Image merge — the builders already ignore it
    # (they gate on an ABSOLUTE path), so reporting it made the panel's summary
    # line, and the cloud dialog's "push this base", describe a run that was never
    # going to happen. Report the effective base ('') and say why, once, instead.
    _stored_base = ds.train_base_model or ''
    _base_mismatch = lt.foreign_base_message(ds.train_type or 'zimage', _stored_base)
    return jsonify({'bases': bases, 'base': '' if _base_mismatch else _stored_base,
                    # Present ONLY when the persisted base belongs to another
                    # family: the note the panel shows so the change isn't silent.
                    'base_family_mismatch': _base_mismatch,
                    # « Custom weights… » (local-only) : chemin custom persisté +
                    # overrides SDXL (VAE/TE). Le sélecteur les ressème ; la
                    # whitelist par famille est ré-appliquée au lancement (400).
                    'vae_path': ds.train_vae_path or '',
                    'te_path': ds.train_te_path or '',
                    'custom_weights_families': list(lt.CUSTOM_WEIGHTS_FAMILIES),
                    'vae_te_families': list(lt.VAE_TE_OVERRIDE_FAMILIES),
                    # Défaut family-aware : Krea → Raw (reco officielle), FLUX.2 Klein
                    # → 4B, sinon Turbo. Déféré au service (_default_variant_for) pour
                    # que l'UI et le lancement (_krea_is_raw/_flux2klein_is_9b) s'accordent.
                    'variant': ds.train_variant or lt._default_variant_for(ds.train_type or 'zimage'),
                    'converted': converted,
                    'convert': zc.convert_status(),
                    'train_type': ds.train_type or 'zimage',
                    'comfyui_configured': comfyui_configured,
                    'models_dir': str(models_dir) if models_dir else '',
                    # Réglages avancés effectifs (persistés ∪ défauts family-aware) pour
                    # la famille courante : rank/alpha/resolution/save_every → le panneau
                    # « Advanced options » les affiche et laisse les éditer.
                    'train_settings': lt.effective_train_settings(ds),
                    # Slider LoRA mode (Beta) : état + prompts persistés + knobs résolus
                    # (colonne dédiée train_slider — jamais écrasé par un preset).
                    'slider': lt.effective_slider_settings(ds),
                    # Can this machine actually train Anima? The arch is an ai-toolkit
                    # EXTENSION, so an older checkout simply doesn't have it (the launch
                    # refuses with a 400). Exposed here rather than in /api/capabilities
                    # because the check walks the extensions tree: base-info is fetched
                    # when the training panel opens, capabilities is polled every 30s.
                    # The panel uses it to stay quiet instead of recommending Anima to
                    # someone who cannot run it.
                    'anima_supported': lt._aitoolkit_supports_anima(),
                    'bases_by_type': {'zimage': bases, 'sdxl': sdxl_bases,
                                      'krea': krea_bases, 'flux': flux_bases,
                                      'flux2klein': flux2klein_bases}})


@bp.post('/dataset/<int:dataset_id>/train/settings')
def dataset_train_settings(dataset_id):
    """Persiste un patch de réglages avancés {rank?, resolution?, save_every?} sur le
    dataset (validé + borné côté service). Renvoie les réglages effectifs résultants."""
    gate = _require_aitoolkit()
    if gate:
        return gate
    d = request.get_json(silent=True) or {}
    try:
        eff = lt.update_train_settings(LOCAL_USER, dataset_id, d)
    except ValueError as e:
        return _map_error(e)
    return jsonify({'ok': True, 'train_settings': eff})


@bp.post('/dataset/<int:dataset_id>/train/slider')
def dataset_train_slider(dataset_id):
    """Slider LoRA mode (Beta) : persiste un patch {enabled?, positive?, negative?,
    target_class?, anchor?, guidance?, anchor_strength?} (validé côté service,
    colonne dédiée train_slider). Renvoie l'état slider effectif."""
    gate = _require_aitoolkit()
    if gate:
        return gate
    d = request.get_json(silent=True) or {}
    try:
        eff = lt.update_slider_settings(LOCAL_USER, dataset_id, d)
    except ValueError as e:
        return _map_error(e)
    return jsonify({'ok': True, 'slider': eff})


# --- Training presets ---------------------------------------------------------
# Named, shareable snapshots of the advanced settings. Stored AS-IS (raw keys);
# validation happens at APPLY time through the per-key path, so a preset file
# from another app version degrades gracefully (unknown keys ignored, invalid
# values reported). No ai-toolkit gate: presets are pure configuration.

_STYLE_SAMPLE_PROMPTS = [
    'a woman reading in a sunlit cafe',
    'a city street at night, rain, neon reflections',
    'a mountain landscape, wide shot, morning mist',
    'a still life of fruit on a wooden table',
    'a cozy interior, warm lamp light',
    'a runner mid-stride on a bridge, motion',
    'a cat sleeping on a windowsill',
    'a modern building facade, strong shadows',
]


def _style_preset_settings(rank, alpha, resolution='768,1024',
                           timestep_type=None):
    """One researched Style baseline with family-specific architecture levers.

    The prompts deliberately describe content only. Style mode is always-on, so
    the dataset's internal run identifier must never become a hidden activation
    token. Network dropout is intentionally absent: Style caption dropout is a
    separate, family-aware service policy and must not be conflated with it.
    """
    out = {
        'rank': rank,
        'alpha': alpha,
        'resolution': resolution,
        'save_every': 250,
        'max_step_saves': 10,
        'sample_every': 250,
        'sample_prompts': list(_STYLE_SAMPLE_PROMPTS),
    }
    if timestep_type:
        out['timestep_type'] = timestep_type
    return out


# Route-owned metadata wraps the validated setting dictionaries. Keeping scope
# outside train_settings means old exported presets remain schema-tolerant while
# new built-ins can be rejected before a single dataset field is mutated.
_STYLE_BUILTIN_PRESETS = [
    # 32/32 linear = the cleanest published Krea recipe (RunComfy "Train on
    # Raw, validate on Turbo": linear timesteps + flowmatch, rank/alpha 32) and
    # the vault's strongest confirmation ("Every Krea-2 source uses 32/32").
    {
        'id': 'builtin-style-krea-raw',
        'name': 'Krea 2 · Style (Raw)',
        'train_type': 'krea',
        'dataset_kind': 'style',
        # ``base`` is the canonical UI value; ``raw`` is accepted as a readable
        # compatibility spelling for callers that used the model's public name.
        'variants': ['base', 'raw'],
        'builtin': True,
        'description': "Krea's own style path — rank 32/32 with linear "
                       'timesteps, trained on Raw (validate on Turbo); '
                       'content-only probes every 250 steps.',
        'settings': _style_preset_settings(32, 32, timestep_type='linear'),
    },
    # weighted = Klein's canonical timestep (ai-toolkit options.ts); rank 32 =
    # the community's style step-up from the 16 default (RunComfy; the Herbst
    # 50-run study points even higher, 128/64, above this app's rank ceiling).
    {
        'id': 'builtin-style-klein-base',
        'name': 'FLUX.2 Klein · Style',
        'train_type': 'flux2klein',
        'dataset_kind': 'style',
        'variants': ['4b', '9b'],
        'builtin': True,
        'description': "Rank 32/32 with Klein's canonical weighted timesteps; "
                       'BFL recommends the shorter step envelope for style — '
                       'content-only probes every 250 steps.',
        'settings': _style_preset_settings(32, 32, timestep_type='weighted'),
    },
    # 32/32 confirmed by the concept research ("32/32 worked for everything,
    # style included"); weighted = the zimage arch default in options.ts and
    # the community's non-character recommendation.
    {
        # id kept ('...-base') for saved references, but the recipe is the
        # Z-Image ARCH DEFAULT (weighted timesteps), not a Base-only choice — so
        # it now applies to every Z-Image variant (Turbo / Base / De-Turbo), like
        # the FLUX.1 and SDXL style presets. Previously gated to ['base'], which
        # left a Turbo Z-Image style dataset with no built-in style preset.
        'id': 'builtin-style-zimage-base',
        'name': 'Z-Image · Style',
        'train_type': 'zimage',
        'dataset_kind': 'style',
        'variants': [],
        'builtin': True,
        'description': 'Rank 32/32 with weighted timesteps (the Z-Image arch '
                       'default, all variants); content-only probes so no hidden '
                       'trigger leaks into an always-on style.',
        'settings': _style_preset_settings(32, 32, timestep_type='weighted'),
    },
    # Corrected from 16/16 (the canonical FLUX subject dimension): the concept
    # research groups FLUX with the 32/32 prose family for style ("start
    # 32/32"), matching the practitioner consensus that style wants more
    # capacity than subject training.
    {
        'id': 'builtin-style-flux1',
        'name': 'FLUX.1 dev · Style',
        'train_type': 'flux',
        'dataset_kind': 'style',
        # FLUX.1 has one training recipe; the historical dataset variant field
        # is irrelevant for it, hence no variant restriction.
        'variants': [],
        'builtin': True,
        'description': 'Style wants more capacity than the 16/16 subject '
                       'default: rank 32/32 (research consensus) with weighted '
                       'timesteps and 250-step probes.',
        'settings': _style_preset_settings(32, 32, timestep_type='weighted'),
    },
    # Corrected from 32/16: the concept research recommends FULL alpha for
    # style ("Alpha = dim, recommandé style") — half-strength stays a
    # character-recipe trick. SDXL is ddpm: no flow-match timestep weighting.
    {
        'id': 'builtin-style-sdxl',
        'name': 'SDXL · Style',
        'train_type': 'sdxl',
        'dataset_kind': 'style',
        'variants': [],
        'builtin': True,
        'description': 'Full-strength rank 32/32 at native 1024 — research '
                       'recommends alpha = rank for style (half-strength is a '
                       'character trick).',
        'settings': _style_preset_settings(32, 32, resolution='1024'),
    },
]


def _builtin_train_presets():
    """Public built-in catalogue, with the legacy generic Style entry hidden.

    Copy every object so route metadata never mutates lora_training's module
    constants (important for tests and for long-lived Flask workers).
    """
    out = []
    seen = set()
    for source in (*lt.BUILTIN_TRAIN_PRESETS, *_STYLE_BUILTIN_PRESETS):
        preset_id = source.get('id')
        if preset_id == 'builtin-style' or preset_id in seen:
            continue
        preset = dict(source)
        preset['settings'] = dict(source.get('settings') or {})
        # Every current entry carries explicit scope metadata; the setdefaults
        # only shield hypothetical future entries from missing keys.
        preset.setdefault('dataset_kind', None)
        preset.setdefault('variants', [])
        out.append(preset)
        seen.add(preset_id)
    return out


_STYLE_PRESET_ID_BY_FAMILY = {
    'krea': 'builtin-style-krea-raw',
    'flux2klein': 'builtin-style-klein-base',
    'zimage': 'builtin-style-zimage-base',
    'flux': 'builtin-style-flux1',
    'sdxl': 'builtin-style-sdxl',
}


def _builtin_preset_by_id(preset_id, train_type):
    """Resolve a public ID, including the pre-family ``builtin-style`` alias."""
    if preset_id == 'builtin-style':
        preset_id = _STYLE_PRESET_ID_BY_FAMILY.get(train_type)
    return next((p for p in _builtin_train_presets()
                 if p.get('id') == preset_id), None)


def _dataset_kind(ds):
    return (getattr(ds, 'kind', None) or 'character').strip().lower()


def _normalise_preset_kind(value):
    kind = str(value or '').strip().lower()
    return kind if kind in svc.DATASET_KINDS else None


def _normalise_preset_variants(values, train_type):
    """Validated, de-duplicated recipe variants; ``None`` means bad input."""
    if values is None:
        return []
    if not isinstance(values, list):
        return None
    family = svc.normalize_train_type(train_type)
    if family in ('flux', 'sdxl'):
        allowed = set()
    else:
        allowed = set(lt._valid_variants_for(family))
        if family == 'krea':
            allowed.add('raw')
    out = []
    for value in values:
        variant = str(value or '').strip().lower()
        if not variant or variant not in allowed:
            return None
        if variant not in out:
            out.append(variant)
    return out


def _preset_scope_error(preset, ds, variant, reason):
    return jsonify({
        'ok': False,
        'error': reason,
        'error_code': 'PRESET_SCOPE',
        'preset_scope': {
            'preset_id': preset.get('id'),
            'preset_train_type': preset.get('train_type'),
            'preset_dataset_kind': preset.get('dataset_kind'),
            'preset_variants': preset.get('variants') or [],
            'dataset_train_type': ds.train_type or 'zimage',
            'dataset_kind': _dataset_kind(ds),
            'variant': variant,
        },
    }), 409


def _validate_preset_scope(preset, ds, requested_train_type=None,
                           requested_variant=None):
    """Return ``None`` when compatible, otherwise a structured 409 response.

    Validation happens wholly before ``apply_train_settings_dict``. This makes a
    stale preset selection harmless even though applying a preset is a replace
    operation that clears the previous explicit settings first.
    """
    dataset_family = ds.train_type or 'zimage'
    if requested_train_type:
        selected_family = str(requested_train_type).strip().lower()
        if selected_family not in svc.TRAIN_TYPES:
            return _preset_scope_error(
                preset, ds, requested_variant,
                'The requested model family is not supported.')
        if selected_family != dataset_family:
            return _preset_scope_error(
                preset, ds, requested_variant,
                'The selected model family changed before this preset was applied.')
    preset_family = preset.get('train_type')
    if preset_family and preset_family != dataset_family:
        return _preset_scope_error(
            preset, ds, requested_variant,
            f'This preset is for {preset_family}, not {dataset_family}.')
    preset_kind = preset.get('dataset_kind')
    if preset_kind and preset_kind != _dataset_kind(ds):
        return _preset_scope_error(
            preset, ds, requested_variant,
            f'This preset is for {preset_kind} datasets, not {_dataset_kind(ds)}.')
    variant = str(
        requested_variant or getattr(ds, 'train_variant', None)
        or lt._default_variant_for(dataset_family)).strip().lower()
    allowed = [str(v).strip().lower() for v in (preset.get('variants') or [])]
    if allowed and variant not in allowed:
        return _preset_scope_error(
            preset, ds, variant,
            f'This preset requires variant {" or ".join(allowed)}, not {variant}.')
    return None


def _preset_payload(p):
    import json
    try:
        settings = json.loads(p.settings or '{}')
    except ValueError:
        settings = {}
    if not isinstance(settings, dict):
        settings = {}
    try:
        variants = json.loads(p.variants or '[]')
    except (TypeError, ValueError):
        variants = []
    if not isinstance(variants, list):
        variants = []
    return {'id': p.id, 'name': p.name, 'train_type': p.train_type,
            # Existing DB rows have NULL scope metadata and remain deliberately
            # usable; their family is still validated at apply time.
            'dataset_kind': _normalise_preset_kind(p.dataset_kind),
            'variants': variants,
            'settings': settings}


@bp.get('/train/presets')
def train_presets_list():
    """Built-ins first (shipped with the app and read-only), then user presets.

    The old generic ``builtin-style`` is intentionally absent: callers should
    select the family recipe. Its ID is still accepted by the apply endpoint.
    """
    from ..models import TrainingPreset
    rows = TrainingPreset.query.order_by(TrainingPreset.name).all()
    return jsonify({'presets': [*_builtin_train_presets(),
                                *(_preset_payload(p) for p in rows)]})


@bp.post('/train/presets')
def train_presets_save():
    """Create or overwrite (by name). Two sources: `dataset_id` snapshots that
    dataset's current explicit settings (the 💾 Save-current path); `settings`
    stores an explicit dict (the ⬆ import path)."""
    import json
    from ..extensions import db
    from ..models import TrainingPreset
    d = request.get_json(silent=True) or {}
    name = (d.get('name') or '').strip()[:80]
    if not name:
        return jsonify({'error': 'name required'}), 400
    requested_family = None
    if 'train_type' in d and d.get('train_type') is not None:
        requested_family = str(d.get('train_type')).strip().lower()
        if requested_family not in svc.TRAIN_TYPES:
            return jsonify({'error': 'invalid train_type'}), 400
    dataset_kind = _normalise_preset_kind(d.get('dataset_kind'))
    if d.get('dataset_kind') is not None and dataset_kind is None:
        return jsonify({'error': 'invalid dataset_kind'}), 400
    supplied_variants = None
    if 'variants' in d:
        supplied_variants = d.get('variants')
    elif 'variant' in d:
        supplied_variants = [d.get('variant')]
    if d.get('dataset_id') is not None:
        ds = svc.get_dataset(LOCAL_USER, d['dataset_id'])
        if not ds:
            return jsonify({'error': 'dataset not found'}), 404
        train_type = ds.train_type or 'zimage'
        if (requested_family is not None
                and requested_family != train_type):
            return jsonify({
                'ok': False,
                'error': 'The selected model family changed before this preset was saved.',
                'error_code': 'PRESET_SCOPE',
            }), 409
        actual_kind = _dataset_kind(ds)
        if dataset_kind is not None and dataset_kind != actual_kind:
            return jsonify({
                'ok': False,
                'error': 'The dataset kind changed before this preset was saved.',
                'error_code': 'PRESET_SCOPE',
            }), 409
        settings = lt.snapshot_train_settings(LOCAL_USER, ds.id)
        dataset_kind = actual_kind
        variants = _normalise_preset_variants(supplied_variants, train_type)
        if variants is None:
            return jsonify({'error': 'invalid variants for train_type'}), 400
        if supplied_variants is None:
            # A snapshot is a recipe for the currently selected architecture.
            # Single-recipe families do not need a synthetic variant scope.
            if train_type in ('flux', 'sdxl'):
                variants = []
            else:
                selected = (d.get('variant') or ds.train_variant
                            or lt._default_variant_for(train_type))
                variants = _normalise_preset_variants([selected], train_type)
                if variants is None:
                    return jsonify({'error': 'invalid variant for train_type'}), 400
    else:
        train_type = requested_family or 'zimage'
        variants = _normalise_preset_variants(supplied_variants, train_type)
        if variants is None:
            return jsonify({'error': 'invalid variants for train_type'}), 400
        settings = d.get('settings')
        if not isinstance(settings, dict):
            return jsonify({'error': "'settings' must be an object"}), 400
    row = TrainingPreset.query.filter_by(name=name).first()
    created = row is None
    if created:
        row = TrainingPreset(name=name)
        db.session.add(row)
    row.train_type = train_type
    row.dataset_kind = dataset_kind
    row.variants = json.dumps(variants) if variants else None
    row.settings = json.dumps(settings)
    db.session.commit()
    return jsonify({'ok': True, 'created': created, **_preset_payload(row)})


@bp.delete('/train/presets/<int:preset_id>')
def train_presets_delete(preset_id):
    from ..extensions import db
    from ..models import TrainingPreset
    row = db.session.get(TrainingPreset, preset_id)
    if not row:
        return jsonify({'error': 'not found'}), 404
    db.session.delete(row)
    db.session.commit()
    return jsonify({'ok': True})


@bp.post('/dataset/<int:dataset_id>/train/presets/apply')
def dataset_train_preset_apply(dataset_id):
    """Replace the dataset's advanced settings with a preset's ({preset_id})
    or with a raw dict ({settings}). Returns the effective settings plus what
    was ignored (unknown keys) and rejected (invalid values). Built-ins and DB
    presets are scope-checked before mutation; raw settings keep the legacy,
    schema-tolerant import path."""
    import json
    from ..extensions import db
    from ..models import TrainingPreset
    d = request.get_json(silent=True) or {}
    ds = svc.get_dataset(LOCAL_USER, dataset_id)
    if not ds:
        return jsonify({'error': 'not found'}), 404
    applied_id = None
    if d.get('preset_id') is not None:
        raw_id = d.get('preset_id')
        applied_id = raw_id
        builtin = (_builtin_preset_by_id(raw_id, ds.train_type or 'zimage')
                   if isinstance(raw_id, str) else None)
        if builtin:
            scoped = _validate_preset_scope(
                builtin, ds, requested_train_type=d.get('train_type'),
                requested_variant=d.get('variant'))
            if scoped:
                return scoped
            settings = dict(builtin.get('settings') or {})
            applied_id = builtin['id']
        else:
            try:
                numeric_id = int(raw_id)
            except (TypeError, ValueError):
                return jsonify({'error': 'unknown preset'}), 404
            row = db.session.get(TrainingPreset, numeric_id)
            if not row:
                return jsonify({'error': 'unknown preset'}), 404
            try:
                row_variants = json.loads(row.variants or '[]')
            except (TypeError, ValueError):
                row_variants = []
            if not isinstance(row_variants, list):
                row_variants = []
            # Legacy numeric presets have always carried a family. New rows also
            # carry kind/variant scope; NULL/[] retains historical compatibility.
            db_preset = {
                'id': row.id,
                'train_type': row.train_type,
                'dataset_kind': row.dataset_kind,
                'variants': row_variants,
            }
            scoped = _validate_preset_scope(
                db_preset, ds, requested_train_type=d.get('train_type'),
                requested_variant=d.get('variant'))
            if scoped:
                return scoped
            try:
                settings = json.loads(row.settings or '{}')
            except ValueError:
                settings = {}
            if not isinstance(settings, dict):
                settings = {}
            applied_id = row.id
    else:
        settings = d.get('settings')
        if not isinstance(settings, dict):
            return jsonify({'error': "'settings' must be an object"}), 400
    try:
        eff, ignored, rejected = lt.apply_train_settings_dict(LOCAL_USER, dataset_id, settings)
    except ValueError as e:
        return _map_error(e)
    return jsonify({'ok': True, 'preset_id': applied_id,
                    'train_type': ds.train_type or 'zimage',
                    'variant': (d.get('variant') or ds.train_variant
                                or lt._default_variant_for(ds.train_type or 'zimage')),
                    'train_settings': eff,
                    'ignored': ignored, 'rejected': rejected})


@bp.post('/dataset/<int:dataset_id>/train/prepare-base')
def dataset_train_prepare_base(dataset_id):
    """Convertit un merge ComfyUI en diffusers (thread d'arrière-plan) pour
    pouvoir entraîner dessus. Statut via /train/base-info (convert)."""
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    bm = (request.get_json(silent=True) or {}).get('base_model', '')
    if not bm:
        return jsonify({'error': 'base model required'}), 400
    # Whitelist stricte : seul un modèle Z-Image réellement listé est convertible
    # (anti path-traversal - l'entrée transporte un chemin jusqu'à un subprocess).
    if bm not in get_zimage_models():
        return jsonify({'error': 'unknown base model'}), 400
    if zc.is_converted(bm):
        return jsonify({'ok': True, 'status': 'done'})
    try:
        zc.start_convert_async(current_app._get_current_object(), bm)
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, 'status': 'running'})


@bp.post('/dataset/<int:dataset_id>/train/open-folder')
def dataset_train_open_folder(dataset_id):
    """Ouvre un dossier dans l'explorateur du poste (app locale) : target 'loras'
    (import ComfyUI de la famille), 'run' (checkpoints du run) ou 'dataset'
    (images + captions .txt du dataset — pas de dépendance ai-toolkit).
    Chemins résolus serveur — le body ne transporte jamais de chemin."""
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    d = request.get_json(silent=True) or {}
    kw = {'target': d.get('target') or 'loras'}
    if d.get('train_type'):
        kw['family'] = d.get('train_type')
    if 'base_model' in d:
        kw['base_model'] = d.get('base_model')
    if d.get('variant'):
        kw['variant'] = d.get('variant')
    try:
        path = lt.open_training_folder(LOCAL_USER, dataset_id, **kw)
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, 'path': path})


@bp.post('/dataset/<int:dataset_id>/train/checkpoint/delete')
def dataset_train_checkpoint_delete(dataset_id):
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    body = request.get_json(silent=True) or {}
    fn = body.get('filename', '')
    fam = body.get('train_type') or None
    try:
        removed = lt.delete_imported_checkpoint(LOCAL_USER, dataset_id, fn, family=fam)
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, 'removed': removed})


@bp.post('/dataset/<int:dataset_id>/train/run-checkpoint/delete')
def dataset_train_run_checkpoint_delete(dataset_id):
    """Move ONE RUN checkpoint to the trash — run-dir file, or a cloud run's
    synced save when cloud_run_id is given (the deployed-LoRA delete above is
    a separate route). Nothing is destroyed until 'Empty trash' in Settings."""
    gate = _require_aitoolkit()
    if gate and not capabilities.probe().get('cloud_training'):
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    body = request.get_json(silent=True) or {}
    try:
        if body.get('cloud_run_id'):
            removed = ct.delete_cloud_checkpoint(dataset_id, body['cloud_run_id'],
                                                 body.get('filename', ''))
        else:
            kw = {} if 'base_model' not in body else {'base_model': body.get('base_model')}
            if body.get('train_type'):
                kw['family'] = body.get('train_type')
            if body.get('variant'):
                kw['variant'] = body.get('variant')
            removed = lt.delete_checkpoint(LOCAL_USER, dataset_id,
                                           body.get('filename', ''), **kw)
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, 'removed': removed})


@bp.post('/dataset/<int:dataset_id>/train/checkpoints/cleanup')
def dataset_train_checkpoints_cleanup(dataset_id):
    """'Clean up this run': trash every run-dir checkpoint NOT in keep_filenames
    (typically final + best-epoch)."""
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    body = request.get_json(silent=True) or {}
    kw = {} if 'base_model' not in body else {'base_model': body.get('base_model')}
    if body.get('train_type'):
        kw['family'] = body.get('train_type')
    if body.get('variant'):
        kw['variant'] = body.get('variant')
    try:
        res = lt.cleanup_checkpoints(LOCAL_USER, dataset_id,
                                     body.get('keep_filenames') or [], **kw)
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **res})


@bp.post('/dataset/train/cloud/purge')
def dataset_train_cloud_purge():
    """Trash the staging dirs of finished cloud runs (dataset copies, samples,
    checkpoint duplicates already imported)."""
    return jsonify({'ok': True, **ct.purge_finished_runs()})


@bp.get('/dataset/train/cloud/staging-sizes')
def dataset_train_cloud_staging_sizes():
    """How much disk each cloud run's staging dir still holds, so the Runs hub can
    show "8.2 GB on disk" on a card and name that weight in the per-run 🧹
    confirmation. DELIBERATELY its own endpoint (and not a field of the runs
    payload): sizing means walking thousands of files, which must not ride the
    hub's 5 s poll. Optional ?run_ids=1,2,3 narrows the walk to the shown cards."""
    raw = (request.args.get('run_ids') or '').strip()
    ids = None
    if raw:
        try:
            ids = [int(x) for x in raw.split(',') if x.strip()]
        except ValueError:
            return jsonify({'error': 'run_ids must be a comma-separated list of run ids'}), 400
    sizes = ct.staging_sizes(ids)
    return jsonify({'ok': True,
                    'sizes': {str(k): v for k, v in sizes.items()},
                    'total_bytes': sum(sizes.values())})


@bp.post('/dataset/train/cloud/purge-run')
def dataset_train_cloud_purge_run():
    """Trash the staging dir of ONE finished cloud run — targeted cleanup, so a
    45-run history no longer forces an all-or-nothing purge. Spares exactly what
    the global purge spares (active runs, kept pods) via the shared rule."""
    body = request.get_json(silent=True) or {}
    if body.get('run_id') in (None, ''):
        return jsonify({'error': 'run_id is required'}), 400
    try:
        res = ct.purge_run_staging(body['run_id'])
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **res})


@bp.post('/dataset/<int:dataset_id>/train/import')
def dataset_train_import(dataset_id):
    gate = _require_aitoolkit()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    body = request.get_json(silent=True) or {}
    fn = body.get('filename', '')
    # base_model = base du run d'où vient le checkpoint (absente → base persistée) ;
    # train_type = famille sélectionnée (absente → persistée) → même run + même dossier.
    kw = {} if 'base_model' not in body else {'base_model': body.get('base_model')}
    fam = body.get('train_type') or None
    if fam:
        kw['family'] = fam
    if body.get('variant'):
        kw['variant'] = body.get('variant')
    # cloud_run_id: import a CLOUD checkpoint (synced into the run's staging —
    # possibly mid-run) instead of a local ai-toolkit file. The run must belong
    # to this dataset; its dataset version rides along into the deployed name.
    if body.get('cloud_run_id'):
        from ..models import CloudTrainingRun
        crun = CloudTrainingRun.query.get(int(body['cloud_run_id']))
        if not crun or crun.dataset_id != dataset_id or not crun.staging_dir:
            return jsonify({'error': 'unknown cloud run'}), 404
        kw['src_dir'] = crun.staging_dir
        kw['version'] = ct._run_param(crun, 'version')
        # Tag the deployed name with THIS cloud run's id (☁ #N) so importing the
        # same step from two different runs never overwrites one with the other.
        kw['run_id'] = crun.id
        kw['run_source'] = 'cloud'
        # Never route a cloud file through the dataset row: replay the exact
        # family/variant/base stamped at cloud launch. Legacy rows fall back to
        # the request's family/variant, but still use the official empty base.
        kw['base_model'] = ct._run_param(crun, 'base_model') or ''
        cloud_fam = ct._run_param(crun, 'train_type')
        cloud_variant = ct._run_param(crun, 'variant')
        if cloud_fam:
            kw['family'] = cloud_fam
        if cloud_variant:
            kw['variant'] = cloud_variant
    try:
        res = lt.import_checkpoint(LOCAL_USER, dataset_id, fn, return_meta=True, **kw)
    except Exception as e:
        return _map_error(e)
    out = {'ok': True, 'dest': os.path.basename(res['dest'])}
    if res.get('collision'):
        # A different LoRA already used that name — the import was renamed rather
        # than silently overwriting it; tell the UI so it can surface the note.
        out['note'] = (f'A different LoRA already used that name — saved as '
                       f'{res["name"]} to avoid overwriting it.')
    return jsonify(out)


@bp.post('/dataset/<int:dataset_id>/train/cloud')
def dataset_train_cloud(dataset_id):
    gate = _require_cloud()
    if gate:
        return gate
    d = request.get_json(silent=True) or {}
    try:
        res = ct.launch_cloud_training(
            LOCAL_USER, dataset_id,
            # No hardcoded 'turbo' default: an absent variant now resolves to
            # the family-aware default in the service (Krea → Raw, like local).
            steps=d.get('steps'),
            base_model=d.get('base_model', ''),
            variant=d.get('variant'),
            train_type=d.get('train_type'),
            masked=d.get('masked'),
            allow_caption_mismatch=bool(d.get('allow_caption_mismatch')),
            allow_uncaptioned=bool(d.get('allow_uncaptioned')),
            allow_caption_quality=bool(d.get('allow_caption_quality')),
            allow_unverified_weights=bool(d.get('allow_unverified_weights')),
            allow_not_ready=bool(d.get('allow_not_ready')),
            gpu_name=d.get('gpu_name'))
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **res})


@bp.get('/dataset/<int:dataset_id>/train/cloud/custom-base')
def dataset_train_cloud_custom_base(dataset_id):
    """Readiness of a CUSTOM base for cloud training: is it already pushed to
    the private `lds-base-<hash>` repo on the user's Hugging Face account
    (cache-hit → launch straight away), or does it need the one-time push?
    Also reports the background push job's state (poll-friendly, never 500s
    on a missing repo — that is just ready=false)."""
    gate = _require_cloud()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    from ..services import hf_base_push
    try:
        state = hf_base_push.base_push_state(
            LOCAL_USER, dataset_id,
            request.args.get('train_type'), request.args.get('variant'),
            (request.args.get('base_model') or '').strip(),
            cfg.secret('HF_TOKEN'))
    except hf_base_push.HfPublishError as e:
        return jsonify({'error': e.message, 'error_code': e.code}), 400
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **state})


@bp.post('/dataset/<int:dataset_id>/train/cloud/custom-base/push')
def dataset_train_cloud_custom_base_push(dataset_id):
    """One-time background upload of the custom base to a PRIVATE repo on the
    user's Hugging Face account (private is forced server-side — no toggle).
    Multi-GB → daemon thread; the UI polls the custom-base route above. The
    confirmable CUSTOM_WEIGHTS_UNVERIFIED arch sniff answers synchronously so
    the dialog can confirm-and-retry."""
    gate = _require_cloud()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    token = cfg.secret('HF_TOKEN')
    if not token:
        return jsonify({'error': 'no Hugging Face token configured — paste an '
                        'HF_TOKEN in Settings ▸ API keys'}), 400
    d = request.get_json(silent=True) or {}
    from ..services import hf_base_push
    try:
        out = hf_base_push.start_push(
            current_app._get_current_object(), dataset_id,
            d.get('train_type'), d.get('variant'),
            (d.get('base_model') or '').strip(), token,
            allow_unverified_weights=bool(d.get('allow_unverified_weights')))
    except hf_base_push.HfPublishError as e:
        return jsonify({'error': e.message, 'error_code': e.code}), 400
    except ValueError as e:
        # preflight_custom_paths' confirmable marker (CUSTOM_WEIGHTS_UNVERIFIED)
        return jsonify({'error': str(e)}), 400
    return jsonify({'ok': True, **out})


@bp.post('/dataset/train/retry')
def dataset_train_retry():
    """↻ Retry a FAILED LOCAL run (Runs page): relaunch training with the exact
    identity params stamped for that launch. A real launch_training — normal
    preflight, GPU-collision refusal, no bypass — replaying the live dataset
    (slider settings included), not a resurrection of the dead process.

    The confirmable refusals are answered HERE, in the payload, exactly like the
    Start handlers above — not inherited from the failed launch. Retry re-exports
    the LIVE dataset, so the guards run against today's images: a consent given
    for "1 image has no caption" must not silently wave through the twelve that
    lost their caption since. Same reason the flags default to False: a retry is
    a launch, and a launch asks. Reported by 1Tomber (GitHub #23), whose retry
    was refused with no way to confirm and no way to see why."""
    gate = _require_aitoolkit()
    if gate:
        return gate
    d = request.get_json(silent=True) or {}
    try:
        res = lt.retry_local_run(
            LOCAL_USER, int(d.get('record_id') or 0),
            **{k: bool(d.get(k)) for k in lt.CONFIRMATION_FLAGS})
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **res})


@bp.post('/dataset/train/cloud/retry')
def dataset_train_cloud_retry():
    """↻ Retry d'un run en erreur (page Cloud) : relance avec les paramètres
    exacts du run raté — pod frais, mêmes garde-fous que tout launch."""
    gate = _require_cloud()
    if gate:
        return gate
    d = request.get_json(silent=True) or {}
    try:
        res = ct.retry_cloud_run(LOCAL_USER, int(d.get('run_id') or 0))
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **res})


@bp.post('/dataset/train/cloud/continue')
def dataset_train_cloud_continue():
    """▶ Continue d'un run cloud TERMINÉ (page Runs) : reprend depuis un checkpoint
    harvesté (from_step, défaut = dernier) et vise step_de_reprise + extra_steps —
    pod frais, mêmes garde-fous que tout launch ; le monitor dépose le checkpoint
    sur le pod avant de démarrer (auto-resume ai-toolkit). overrides = réglages sûrs
    (le service refuse toute autre clé → 400)."""
    gate = _require_cloud()
    if gate:
        return gate
    d = request.get_json(silent=True) or {}
    try:
        res = ct.continue_cloud_run(LOCAL_USER, int(d.get('run_id') or 0),
                                    extra_steps=d.get('extra_steps', 1000),
                                    from_step=d.get('from_step'),
                                    overrides=d.get('overrides'))
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **res})


@bp.post('/dataset/<int:dataset_id>/train/cloud/continue-local')
def dataset_train_cloud_continue_local(dataset_id):
    """▶ Continue d'un checkpoint LOCAL dans le CLOUD (voie « Cloud » de la modale
    Continue, côté dataset) : le fichier du run local est semé sur un pod frais
    (resume_ckpt_path) et le job vise step_de_reprise + extra_steps. Mêmes
    garde-fous que tout launch cloud (clé vast.ai, budget, limite de runs actifs,
    unicité par famille) — c'est un launch_cloud_training normal."""
    gate = _require_cloud()
    if gate:
        return gate
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    d = request.get_json(silent=True) or {}
    kw = {'extra_steps': d.get('extra_steps', 1000)}
    if 'base_model' in d:
        kw['base_model'] = d.get('base_model')
    if d.get('variant'):
        kw['variant'] = d.get('variant')
    if d.get('train_type'):
        kw['train_type'] = d.get('train_type')
    if d.get('from_step') is not None:
        kw['from_step'] = d.get('from_step')
    if d.get('overrides') is not None:
        kw['overrides'] = d.get('overrides')
    if d.get('gpu_name'):
        kw['gpu_name'] = d.get('gpu_name')
    kw['masked'] = d.get('masked')
    kw['allow_unverified_weights'] = bool(d.get('allow_unverified_weights'))
    kw['allow_caption_mismatch'] = bool(d.get('allow_caption_mismatch'))
    kw['allow_uncaptioned'] = bool(d.get('allow_uncaptioned'))
    kw['allow_caption_quality'] = bool(d.get('allow_caption_quality'))
    kw['allow_not_ready'] = bool(d.get('allow_not_ready'))
    try:
        res = ct.continue_local_run_in_cloud(LOCAL_USER, dataset_id, **kw)
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **res})


@bp.get('/dataset/<int:dataset_id>/train/cloud/offers')
def dataset_train_cloud_offers(dataset_id):
    """Live GPU speed tiers for the launch dialog (price/h + approx time+cost).
    Read-only — rents nothing; the launch call rents the chosen class."""
    gate = _require_cloud()
    if gate:
        return gate
    try:
        data = ct.gpu_tiers(LOCAL_USER, dataset_id,
                            train_type=request.args.get('train_type'),
                            variant=request.args.get('variant'),
                            steps=request.args.get('steps', type=int))
    except Exception as e:
        return _map_error(e)
    return jsonify({'ok': True, **data})


@bp.get('/dataset/train/cloud/status')
def dataset_train_cloud_status():
    return jsonify(ct.cloud_status())


@bp.get('/dataset/train/cloud/runs')
def dataset_train_cloud_runs():
    """Active + recent cloud runs for the dedicated Cloud-runs hub page.
    Open like status (no gate): an unconfigured backend just returns empties."""
    return jsonify(ct.all_runs(limit=request.args.get('limit', default=20, type=int)))


@bp.get('/dataset/train/runs/<run_key>/share')
def dataset_train_run_share(run_key):
    """⎘ Share configuration: a paste-safe .txt of EVERYTHING this launch sent
    to ai-toolkit (family/variant/base + the full settings snapshot) plus the
    run's outcome — for sharing a recipe or asking for help on Discord/GitHub.
    `run_key` is 'cloud-<id>' (any cloud run) or 'rec-<id>' (a local run).
    Open like the other Runs-hub reads (no gate): unknown key -> 404."""
    from flask import Response
    from ..services import run_share
    out = run_share.build_run_config_text(run_key)
    if out is None:
        return jsonify({'error': 'unknown run'}), 404
    return Response(
        out['text'], mimetype='text/plain; charset=utf-8',
        headers={'Content-Disposition': f'attachment; filename="{out["filename"]}"'})


@bp.get('/dataset/train/runs/<int:record_id>/lineage')
def dataset_train_run_lineage(record_id):
    """🌳 Genealogy tree of the lineage a run belongs to: nodes (every launch
    linked by continuations, local + cloud) and parent→child edges. Addressed
    by TrainingRunRecord id — the universal run node key (cloud rows expose it
    as record_id too). Open like the other Runs-hub reads: unknown id → 404."""
    tree = ct.run_lineage(record_id)
    if not tree.get('nodes'):
        return jsonify({'error': 'unknown run'}), 404
    return jsonify(tree)


@bp.get('/dataset/train/runs/compare')
def dataset_train_runs_compare():
    """Everything that differs between two runs: recipe, dataset (added/removed
    images, edited captions WITH their text, re-edited pixels) and the machine.

    Query: `?a=<record_id>&b=<record_id>`. Deliberately its own read rather than
    a fatter lineage payload — caption text is kilobytes per run and the graph
    draws dozens of nodes. Unknown id → 404."""
    from ..services import run_compare
    try:
        a = int(request.args.get('a', ''))
        b = int(request.args.get('b', ''))
    except (TypeError, ValueError):
        return jsonify({'error': 'two run ids are required'}), 400
    out = run_compare.compare(a, b)
    if out.get('error'):
        return jsonify(out), 404
    return jsonify(out)


@bp.get('/dataset/runs/archive/<sig>')
def dataset_run_archive_blob(sig):
    """Serve an ARCHIVED training image by its content hash — the only way to
    look at an image that has since been deleted from its dataset. Unknown or
    never-archived hash → 404 (the panel then says the picture is unavailable
    instead of showing a wrong one)."""
    from flask import send_file
    from ..services import run_archive
    path = run_archive.path_for(sig)
    if not path:
        return jsonify({'error': 'not archived'}), 404
    return send_file(path, max_age=31536000)


@bp.get('/dataset/train/runs/<int:record_id>/deletion-impact')
def dataset_train_run_deletion_impact(record_id):
    """What deleting this run would take with it, counted — read by the
    confirmation dialog so a destructive action is announced BEFORE it happens.

    Returns checkpoint notes, preview links, generated images that would lose
    their provenance (they are unlinked, never deleted), canvas positions,
    children that would be detached, and archived source images this run is the
    last referrer of. Unknown id → 404."""
    impact = ct.run_deletion_impact(record_id)
    if impact is None:
        return jsonify({'error': 'unknown run'}), 404
    return jsonify(impact)


@bp.delete('/dataset/train/runs/<int:record_id>')
def dataset_train_run_delete(record_id):
    """Remove a GONE run (no checkpoints on disk) from the lineage graph with
    everything that only existed for it: the record, its checkpoint notes, its
    preview links and its canvas position. Generated images are UNLINKED, not
    deleted; archived source blobs are freed only when no other run references
    them. A run whose checkpoints are still on disk is refused with 409 (delete
    those first) — never a silent erase. Children that resumed from it are
    detached, not deleted. Unknown id → 404.

    `?cascade=1` is the OPT-IN destructive mode the run panel's "Delete run"
    asks for: the checkpoints go to the trash, the generated images with them,
    then the row. It is a query flag rather than a new default so no existing
    caller of this route starts shredding files because the semantics moved
    under it. Even then children are DETACHED, 👍 images and LoRAs already
    deployed into ComfyUI are KEPT — see services.run_cascade_delete. A dataset
    that is training right now → 409; a checkpoint that could not be moved →
    409 with the counts of what did go, and the run row left in place."""
    if (request.args.get('cascade') or '').lower() in ('1', 'true', 'yes'):
        return _dataset_train_run_delete_cascade(record_id)
    status = ct.delete_run_record(record_id)
    if status == 'not_found':
        return jsonify({'error': 'unknown run'}), 404
    if status == 'has_saves':
        return jsonify({'error': 'This run still has checkpoints on disk. Delete '
                                 'its checkpoints first, then remove the run.'}), 409
    if status == 'conflict':
        return jsonify({'error': 'This run is still referenced and could not be '
                                 'removed. Refresh and try again.'}), 409
    return jsonify({'ok': True})


def _dataset_train_run_delete_cascade(record_id):
    """The `?cascade=1` branch. Split out so the conservative path above reads
    exactly as it did — the two modes share a URL, never a body of code.

    A PARTIAL result is an error (409), not a 200 with a sad number: the run row
    is still there and its remaining weights are still on disk, so telling the
    user "deleted" would be a lie he only discovers on the next refresh. The
    message is already path-redacted by the service."""
    from ..services import run_cascade_delete
    out = run_cascade_delete.delete_run_cascade(record_id)
    status = out.get('status')
    if status == 'not_found':
        return jsonify({'error': 'unknown run'}), 404
    if status == 'training':
        where = ('a cloud pod' if out.get('error') == 'cloud' else 'this dataset')
        return jsonify({**out, 'error': f'{where} is training right now — stop the '
                                        'run before deleting it.'}), 409
    if status == 'partial':
        return jsonify({**out, 'error': 'Some files could not be removed, so the run '
                                        'was kept. ' + (out.get('error') or '')}), 409
    if status == 'conflict':
        return jsonify({**out, 'error': 'This run is still referenced and could not be '
                                        'removed. Refresh and try again.'}), 409
    return jsonify({**out, 'ok': True})


@bp.put('/dataset/train/runs/<int:record_id>/note')
def dataset_train_run_note(record_id):
    """Save the Lab's free-form note on a run. Unknown run → 404."""
    text = (request.get_json(silent=True) or {}).get('note', '')
    if not ct.set_run_note(record_id, text):
        return jsonify({'error': 'not found'}), 404
    return jsonify({'ok': True})


@bp.put('/dataset/train/runs/<int:record_id>/checkpoints/<int:step>/note')
def dataset_train_checkpoint_note(record_id, step):
    """Save the Lab's free-form note on one checkpoint (record_id, step)."""
    text = (request.get_json(silent=True) or {}).get('note', '')
    if not ct.set_checkpoint_note(record_id, step, text):
        return jsonify({'error': 'not found'}), 404
    return jsonify({'ok': True})


@bp.post('/dataset/<int:dataset_id>/lineage/previews')
def dataset_lineage_generate_previews(dataset_id):
    """🎨 Lab inline generation: render a same-prompt/same-seed preview for each
    selected checkpoint by reusing the Test-Studio engine pinned to those
    checkpoints at strength 1.0. Body: {prompt, seed, family,
    checkpoints:[{record_id, step}]}.

    A training holding the GPU → 409 (a training and a generation never share the
    GPU) — never a silent no-op. No checkpoint deployed for the family → 409
    needs_setup (the same 'set it up first' honesty the rest of the app uses). A
    vision pass holding the GPU, or a ComfyUI that isn't set up, surface through
    the engine as the Studio's usual 503 / structured-409. Unknown dataset → 404."""
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    if ct.training_in_progress():
        return jsonify({'error': 'GPU busy',
                        'detail': 'A LoRA training is running — previews share the '
                                  'GPU with training, so try again once it finishes.'
                        }), 409
    d = request.get_json(silent=True) or {}
    cks = d.get('checkpoints') or []
    if not isinstance(cks, list) or not cks:
        return jsonify({'error': 'no checkpoints selected'}), 400
    try:
        out = ct.generate_checkpoint_previews(
            LOCAL_USER, dataset_id, cks, prompt=d.get('prompt'),
            seed=d.get('seed'), family=d.get('family'))
    except Exception as e:
        return _map_error(e)
    if out.get('needs_setup'):
        return jsonify({'error': 'No deployed checkpoint to preview',
                        'detail': 'None of the selected checkpoints has a deployed '
                                  'LoRA for this family yet — import/deploy it first, '
                                  'then generate a preview.',
                        'needs_setup': True, 'skipped': out.get('skipped', [])}), 409
    return jsonify(out)


@bp.get('/dataset/train/runs/<run_key>/preview')
def dataset_train_run_preview(run_key):
    """Newest sample image a run produced — the Runs-hub card thumbnail.
    `run_key` is 'cloud-<id>' or 'rec-<id>' (same addressing as /share). The
    file path is resolved fully server-side from the run's own record (staging
    dir for cloud, the stamped local run dir otherwise) — the client never
    sends a path. Open like the other Runs-hub reads: unknown/sampleless → 404."""
    from flask import send_file
    p = ct.run_preview_path(run_key)
    if not p:
        return jsonify({'error': 'no preview for this run'}), 404
    return send_file(p, conditional=True)


@bp.get('/dataset/<int:dataset_id>/train/cloud/progress')
def dataset_train_cloud_progress(dataset_id):
    try:
        return jsonify(ct.cloud_progress(LOCAL_USER, dataset_id,
                                         train_type=request.args.get('train_type')))
    except Exception as e:
        return _map_error(e)


@bp.post('/dataset/train/cloud/stop')
def dataset_train_cloud_stop():
    """Stop a cloud run and report what really happened.

    The answer is never a courtesy 'ok': when no monitor thread is in a state
    to honour the request, request_stop terminates the pod itself, and if even
    that fails the payload carries the instance id the user must destroy by
    hand (HTTP stays 200 — the request was understood, the outcome is in the
    body, which is what the UI renders)."""
    d = request.get_json(silent=True) or {}
    res = ct.request_stop(d.get('run_id'))
    if not isinstance(res, dict):       # defensive: legacy bool contract
        res = {'ok': bool(res)}
    return jsonify(res)


@bp.get('/dataset/<int:dataset_id>/train/cloud/sample/<path:filename>')
def dataset_train_cloud_sample(dataset_id, filename):
    from flask import send_from_directory, abort
    # ?train_type= resolves THAT family's newest run (several families may
    # train the same dataset in parallel); absent -> plain newest, unchanged.
    run = ct.latest_run_for(dataset_id, request.args.get('train_type'))
    if not run or not run.staging_dir:
        abort(404)
    # send_from_directory refuses path traversal by construction
    return send_from_directory(os.path.join(run.staging_dir, 'samples'), filename)


@bp.get('/dataset/<int:dataset_id>/train/cloud/checkpoint')
def dataset_train_cloud_checkpoint(dataset_id):
    from flask import send_file, abort
    # ?run_id targets THAT run's file: with several finished runs of a family
    # in the hub history, 'newest run of the family' would serve the WRONG
    # checkpoint from an older row's button.
    rid = request.args.get('run_id', type=int)
    if rid is not None:
        from ..models import CloudTrainingRun
        run = CloudTrainingRun.query.get(rid)
        if run and run.dataset_id != dataset_id:
            run = None
    else:
        run = ct.latest_run_for(dataset_id, request.args.get('train_type'))
    if not run:
        abort(404)
    # ?filename targets ONE harvested epoch in this run's staging (the ◉ Graph's
    # per-checkpoint ⬇). Path-guarded: basename only, and it must really be a
    # .safetensors sitting in THIS run's staging_dir. Absent → the run's final
    # LoRA, the historical behaviour.
    fn = request.args.get('filename')
    if fn:
        safe = os.path.basename(fn)
        if (safe != fn or not safe.lower().endswith('.safetensors')
                or not run.staging_dir):
            abort(404)
        path = os.path.join(run.staging_dir, safe)
        if not os.path.isfile(path):
            abort(404)
        return send_file(path, as_attachment=True)
    if not run.checkpoint_local_path or not os.path.isfile(run.checkpoint_local_path):
        abort(404)
    return send_file(run.checkpoint_local_path, as_attachment=True)


@bp.get('/dataset/<int:dataset_id>/train/checkpoint/file')
def dataset_train_checkpoint_file(dataset_id):
    """Download ONE local run-dir checkpoint by filename — the ◉ Graph's
    per-checkpoint ⬇ for local runs (the cloud sibling is train/cloud/checkpoint
    ?filename). Path-guarded server-side to this run's own saves (see
    lt.checkpoint_file_path); the client never sends a path. Unknown → 404."""
    from flask import send_file, abort
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        abort(404)
    fam = request.args.get('train_type') or None
    variant = request.args.get('variant') or None
    bm = request.args.get('base_model')
    kw = {} if bm is None else {'base_model': bm}
    if fam:
        kw['family'] = fam
    if variant:
        kw['variant'] = variant
    path = lt.checkpoint_file_path(
        LOCAL_USER, dataset_id, request.args.get('filename', ''), **kw)
    if not path:
        abort(404)
    return send_file(path, as_attachment=True)


@bp.get('/train/activity')
def train_activity():
    """🏋️ Live "something is training" signal for the nav indicator, local and
    cloud. Ungated and free by design (one flag + one COUNT): every page polls
    it, so it must never probe, touch the disk or reach the network. An
    unconfigured cloud simply reports zero."""
    return jsonify(ct.training_activity())


@bp.get('/train/canvas/datasets')
def train_canvas_datasets():
    """◉ LoRA Canvas index: which datasets have runs worth drawing, how many, and
    in which families. Cheap by design (no checkpoints, no disk) — the canvas
    fetches each selected dataset's genealogy separately, so the board and its
    filter appear immediately instead of after a full-library disk scan."""
    return jsonify(ct.canvas_dataset_index(LOCAL_USER))


@bp.post('/train/canvas/generate')
def train_canvas_generate():
    """◉ Generate from the LoRA Canvas — the same Test-Studio engine, driven by
    the checkpoints ticked on the board instead of by a picker. Body:
    {selections:[{dataset_id, checkpoint, record_id, step}], …every Studio
    setting}. Selections MAY span several datasets (that is the point of the
    canvas); they may NOT span several families — the engine refuses, and the
    reason travels back so the button can say it. Same gates as the other launch
    routes: ComfyUI not set up → 409/503, missing models/nodes → the actionable
    409 the Studio already returns."""
    from ._common import (_require_comfyui, _studio_arch_mismatch_response,
                          _studio_missing_response)
    gate = _require_comfyui()
    if gate:
        return gate
    d = request.get_json(silent=True) or {}
    try:
        res = ct.canvas_generate(
            LOCAL_USER, d.get('selections') or [],
            strengths=d.get('strengths') or [1.0],
            seed=d.get('seed'), prompt=d.get('prompt'), z_model=d.get('z_model'),
            aspects=d.get('aspects'), cfgs=d.get('cfgs'), steps_list=d.get('steps'),
            steps2_list=d.get('steps2'), count=d.get('count'),
            permanent_loras=d.get('permanent_loras'), batch_loras=d.get('batch_loras'),
            rebalance=d.get('rebalance'),
            rebalance_strength=d.get('rebalance_strength'),
            negative=d.get('negative'), sampler=d.get('sampler'),
            scheduler=d.get('scheduler'), weight_dtype=d.get('weight_dtype'),
            enhancer=d.get('enhancer'), enhancer_strength=d.get('enhancer_strength'),
            detail_amount=d.get('detail_amount'),
            resolution_tier=d.get('resolution_tier'),
            resolution_multiplier=d.get('resolution_multiplier'),
            init_image=d.get('init_image'), denoise=d.get('denoise'))
    except Exception as e:
        from ..services.lora_test_studio import StudioArchMismatch, StudioAssetsMissing
        if isinstance(e, StudioArchMismatch):
            return _studio_arch_mismatch_response(e)
        if isinstance(e, StudioAssetsMissing):
            return _studio_missing_response(e)
        return _map_error(e)
    return jsonify({'ok': True, **{k: res[k]
                                   for k in ('created', 'seed', 'count', 'run_id')}})


@bp.get('/train/checkpoint/<int:record_id>/<int:step>/images')
def train_checkpoint_images(record_id, step):
    """🖼 Everything this checkpoint ever generated, newest first — the gallery
    the ◉ Canvas opens under a node. Reads the link written at generation time,
    so it holds images made from any surface (Test Studio, canvas, comparison
    grid). Open like the other Runs-hub reads; a checkpoint with no image simply
    answers an empty list plus the `unlinked` counter."""
    return jsonify(ct.checkpoint_gallery(
        record_id, step, limit=request.args.get('limit', default=120, type=int)))


@bp.post('/train/checkpoint/<int:record_id>/<int:step>/images/delete')
def train_checkpoint_images_delete(record_id, step):
    """🗑 Delete generated images from a checkpoint's gallery. Body:
    {image_ids: [id, …]}.

    A real delete: these rows are the Test Studio's cells, so they leave both
    surfaces — the confirmation says so before arming the button. Files are
    disposed of the recoverable way (OS recycle bin, else the app trash, else a
    permanent unlink only when both refuse); the mode used rides back in the
    answer, and `checkpoint_gallery` announces it beforehand. Ids not linked to
    this checkpoint are refused rather than deleted, and per-image failures are
    reported in `skipped` without aborting the batch — an empty selection is a
    no-op, never an error."""
    ids = (request.get_json(silent=True) or {}).get('image_ids') or []
    if not isinstance(ids, list):
        return jsonify({'error': 'image_ids must be a list'}), 400
    try:
        out = ct.delete_checkpoint_images(record_id, step, ids)
    except OSError as e:
        current_app.logger.warning('checkpoint gallery delete failed: %s', e)
        return jsonify({'error': 'Could not delete these images — a file is '
                                 'locked or unreachable. Try again.'}), 500
    return jsonify({'ok': True, **out})


@bp.get('/train/run/<int:record_id>/images')
def train_run_images(record_id):
    """🖼 Everything ONE RUN ever generated, grouped by checkpoint — the gallery
    the ◉ Canvas opens on a run CARD. Shaped like the checkpoint one (same rows,
    same `unlinked` footnote, same announced `delete_mode`), with `groups`
    instead of a flat list: steps descending, the step-less group last.

    Capped, and it says so: `per_step` images per checkpoint, `limit` overall,
    with `truncated` per group and for the whole answer. A run with fourteen
    checkpoints must not answer with a payload nobody can scroll."""
    return jsonify(ct.run_gallery(
        record_id,
        limit=request.args.get('limit', default=None, type=int),
        per_step=request.args.get('per_step', default=None, type=int)))


@bp.post('/train/run/<int:record_id>/images/delete')
def train_run_images_delete(record_id):
    """🗑 Delete generated images from a RUN's gallery. Body: {image_ids: [id, …]}.

    THE checkpoint delete with its scope widened (``step=None``) — same recycle
    bin, same refusal of ids that belong elsewhere, same per-image `skipped`
    report. Ids outside this run are refused, so widening the scope to a run
    never widens it to the library."""
    ids = (request.get_json(silent=True) or {}).get('image_ids') or []
    if not isinstance(ids, list):
        return jsonify({'error': 'image_ids must be a list'}), 400
    try:
        out = ct.delete_checkpoint_images(record_id, None, ids)
    except OSError as e:
        current_app.logger.warning('run gallery delete failed: %s', e)
        return jsonify({'error': 'Could not delete these images — a file is '
                                 'locked or unreachable. Try again.'}), 500
    return jsonify({'ok': True, **out})


def _zip_ids_arg():
    """The optional `ids=1,2,3` selection. Absent → the whole scope; present but
    unparseable → an empty selection, which the plan then refuses out loud. A
    silently-ignored malformed argument would hand over the WHOLE gallery to a
    click that meant "these three"."""
    raw = request.args.get('ids')
    if raw is None:
        return None
    return [p for p in raw.split(',') if p.strip()]


def _gallery_zip(record_id, step):
    """Shared body of the two ZIP routes — see services.gallery_download for why
    the file NAME is the whole feature. The plan runs first so a scope with
    nothing left on disk is refused with a reason instead of answering an empty
    archive; `_zip_download` (routes.datasets) owns the spool whose lifetime has
    to outlive this function."""
    from ..services import gallery_download as gdl
    from .datasets import _zip_download
    plan = gdl.gallery_download_plan(record_id, step, image_ids=_zip_ids_arg())
    if not plan['ok']:
        return jsonify({'error': plan['note']}), 404
    response = _zip_download(lambda out: gdl.write_gallery_zip(plan['entries'], out),
                             plan['filename'])
    # Readable by a fetch() caller, so the panel can state what actually went in
    # even when the archive itself is handed straight to the browser.
    response.headers['X-Lds-Zip-Images'] = str(plan['included'])
    response.headers['X-Lds-Zip-Total'] = str(plan['total'])
    return response


@bp.get('/train/image/<int:image_id>/download')
def train_image_download(image_id):
    """⬇ ONE generated image, under a name that still says where it came from.

    Resolved here rather than left to `<a download>` on the image URL: a file
    that has been cleaned off the disk would otherwise be saved as a 404 page
    wearing a .png name, and the user would find out by opening it."""
    from flask import send_file
    from ..services import gallery_download as gdl
    path, name = gdl.single_image_download(image_id)
    if path is None:
        return jsonify({'error': name}), 404
    return send_file(path, as_attachment=True, download_name=name)


@bp.get('/train/run/<int:record_id>/images/zip')
def train_run_images_zip(record_id):
    """⬇ A whole RUN's gallery as one ZIP — optional `?ids=` for a selection."""
    return _gallery_zip(record_id, None)


@bp.get('/train/run/<int:record_id>/images/zip/plan')
def train_run_images_zip_plan(record_id):
    """What that ZIP would hold, without building it: counts, the cap, and how
    many files have gone missing. The panel asks this BEFORE it downloads so
    every cut is on screen rather than discovered inside the archive."""
    from ..services import gallery_download as gdl
    plan = gdl.gallery_download_plan(record_id, None, image_ids=_zip_ids_arg())
    return jsonify({k: v for k, v in plan.items() if k != 'entries'})


@bp.get('/train/checkpoint/<int:record_id>/<int:step>/images/zip')
def train_checkpoint_images_zip(record_id, step):
    """⬇ One CHECKPOINT's gallery as a ZIP — the run route, narrowed to a step."""
    return _gallery_zip(record_id, step)


@bp.get('/train/checkpoint/<int:record_id>/<int:step>/images/zip/plan')
def train_checkpoint_images_zip_plan(record_id, step):
    """The checkpoint-scoped preflight — same answer, narrower scope."""
    from ..services import gallery_download as gdl
    plan = gdl.gallery_download_plan(record_id, step, image_ids=_zip_ids_arg())
    return jsonify({k: v for k, v in plan.items() if k != 'entries'})


@bp.get('/train/canvas/positions')
def train_canvas_positions():
    """◉ LoRA Canvas: every remembered card position, grouped by dataset id.
    One request for the whole board — the lanes need their overrides before the
    first paint, and N round-trips for a few dozen tiny rows would cost more
    than the genealogy fetches they precede."""
    return jsonify(ct.canvas_positions(LOCAL_USER))


@bp.put('/dataset/<int:dataset_id>/canvas/positions')
def dataset_canvas_positions_save(dataset_id):
    """Remember where cards sit in ONE lane. Body: {positions:[{record_id,x,y}]}.
    Upsert, so re-sending the same coordinates is a no-op — the canvas re-pins a
    lane whenever it gains a run."""
    data = request.get_json(silent=True) or {}
    try:
        return jsonify(ct.save_canvas_positions(
            LOCAL_USER, dataset_id, data.get('positions')))
    except LookupError:
        return jsonify({'error': 'not found'}), 404


@bp.delete('/dataset/<int:dataset_id>/canvas/positions')
def dataset_canvas_positions_clear(dataset_id):
    """✦ Tidy up one lane: forget every dragged position and fall back to the
    automatic tree."""
    try:
        return jsonify(ct.clear_canvas_positions(LOCAL_USER, dataset_id))
    except LookupError:
        return jsonify({'error': 'not found'}), 404


@bp.get('/train/canvas/images')
def train_canvas_images():
    """🖼 Every image pinned on the ◉ LoRA Canvas, grouped by dataset id, with
    the image row alongside its geometry — one request for the whole board, like
    the card positions it sits next to. Rows whose image is gone are pruned
    server-side rather than answered."""
    return jsonify(ct.canvas_image_nodes(LOCAL_USER))


@bp.put('/dataset/<int:dataset_id>/canvas/images')
def dataset_canvas_images_save(dataset_id):
    """Remember pinned images of ONE lane.
    Body: {nodes:[{image_id,x,y,w,h,visible}]}.

    Closing a pinned image is this call with ``visible: false`` — the geometry
    stays, so re-opening puts the picture back exactly where and at the size it
    was closed at."""
    data = request.get_json(silent=True) or {}
    try:
        return jsonify(ct.save_canvas_image_nodes(
            LOCAL_USER, dataset_id, data.get('nodes')))
    except LookupError:
        return jsonify({'error': 'not found'}), 404


@bp.delete('/dataset/<int:dataset_id>/canvas/images')
def dataset_canvas_images_clear(dataset_id):
    """Forget every pinned image of one lane, geometry included. Deliberately
    NOT what ✦ Tidy up calls — see clear_canvas_image_nodes."""
    try:
        return jsonify(ct.clear_canvas_image_nodes(LOCAL_USER, dataset_id))
    except LookupError:
        return jsonify({'error': 'not found'}), 404


@bp.get('/dataset/<int:dataset_id>/train/lineage')
def dataset_train_dataset_lineage(dataset_id):
    """🌳 Genealogy forest of ALL this dataset's runs (every launch + its
    checkpoints), for the ◉ Graph the Checkpoints & LoRAs manager opens.
    Optionally scoped to the family/variant the panel shows (train_type/variant).
    Unlike the per-run lineage there is no single current run. Empty → 200 with
    an empty tree so the caller renders nothing, never an error page."""
    if not svc.get_dataset(LOCAL_USER, dataset_id):
        return jsonify({'error': 'not found'}), 404
    return jsonify(ct.dataset_lineage(
        dataset_id, train_type=request.args.get('train_type') or None,
        variant=request.args.get('variant') or None))

"""Cloud LoRA training orchestrator (vast.ai ephemeral pod).

State machine (CloudTrainingRun.status):
  preparing -> provisioning -> uploading -> training -> downloading
  -> terminating -> done | stopped | error | error_pod_kept

Leak-safety invariant: every path between create_instance() and run
completion must end in destroy_instance() -- enforced here (provision
try/except), by the max-runtime cap (monitor, Task 6) and by boot
reconciliation. The local training path is untouched: a cloud run never sets
'training_in_progress', so local generation/captioning stay available."""
import json
import logging
import os
import re
import secrets as pysecrets
import shutil
import threading
import time
from datetime import datetime
from pathlib import Path

from sqlalchemy import func

from .. import config as cfg
from ..extensions import db
from ..models import CloudTrainingRun
from . import face_dataset_service as fds
from . import gpu_speed
from . import lora_training as lt
from . import vast_client
from .aitoolkit_remote import RemoteAiToolkit

logger = logging.getLogger(__name__)

ACTIVE_STATES = ('preparing', 'provisioning', 'uploading', 'training',
                 'downloading', 'terminating')

_stop_events = {}        # run_id -> threading.Event
_monitor_threads = {}    # run_id -> threading.Thread
_supervisor_thread = None    # the one out-of-monitor watchdog (start_supervisor)
_auto_retry_lock = threading.Lock()

# -- watchdog / stop authority ------------------------------------------------
# A pod bills by the hour, so every guarantee below is anchored on the DATABASE
# (and on the vast API), never on in-process state: a threading.Event does not
# survive a restart and is worthless when the thread meant to observe it is
# dead or wedged.
SUPERVISOR_INTERVAL_SECONDS = 60
# Database silence past which a monitor thread is no longer trusted to carry
# out a stop -- it writes phase_detail every poll (~10 s), so two minutes of
# nothing means it is not coming back in time to save a paid pod.
STOP_HANDOFF_SECONDS = 120
# ... and how long a stop handed to a (then) responsive monitor may stay
# unfinished before the supervisor terminates the pod itself. Generous enough
# to cover the graceful path: stop the remote job, pull the last checkpoint.
STOP_DEADLINE_SECONDS = 15 * 60
# The supervisor defers to a live monitor on the runtime cap (the monitor
# rescues the checkpoint first); it only acts if the monitor did not.
_SUPERVISOR_MARGIN_SECONDS = 120
# Floor for phases that are legitimately silent (staging, boot, upload, final
# download). The runtime cap stays their real backstop.
_SILENT_PHASE_FREEZE_SECONDS = 120 * 60
_FREEZE_WATCHDOG_MINUTES = 45   # default when config carries no value
# Flask serves requests from multiple threads in the portable app.  SQLite
# cannot express the two launch invariants (global active-run cap and
# per-dataset/family uniqueness) as a simple UNIQUE constraint because both
# depend on a set of non-terminal statuses.  Serialize the final guardrail
# re-check and reservation row instead, before any monitor can rent a pod.
_launch_reservation_lock = threading.Lock()
_UNSET = object()
_TRAIN_SETTINGS_SNAPSHOT = 'train_settings_snapshot'
# Slider LoRA mode (Beta) settings live in a DEDICATED column (train_slider),
# not train_settings, so they need their own per-run snapshot: the pod job is
# built minutes after launch (and later on retry/continue), and a toggle-off or
# prompt edit in that window must not retarget an already-launched slider run
# into a plain LoRA (same immutability contract as _TRAIN_SETTINGS_SNAPSHOT —
# see _RunConfigDataset / incident 2026-07-14).
_TRAIN_SLIDER_SNAPSHOT = 'train_slider_snapshot'
_CONFIRMATION_FLAGS = (
    'allow_caption_mismatch',
    'allow_uncaptioned',
    'allow_caption_quality',
    # Custom-weights arch confirm (CUSTOM_WEIGHTS_UNVERIFIED contract): replayed
    # on retry/continue like the caption flags — the base_model is replayed
    # verbatim too, so a confirmed file stays confirmed.
    'allow_unverified_weights',
    # « Continue anyway » ack (readiness floor blocker): replayed on retry/continue
    # like the caption flags, and stamped into train_params so a thin cloud run is
    # honestly explainable in the Runs hub.
    'allow_not_ready',
)


def _confirmation_flags(params) -> dict:
    """Replay only booleans explicitly stamped by the original launch.

    Missing/corrupt legacy values are False: retrying or continuing re-exports
    the mutable current dataset, so an old successful run is never authority to
    waive today's caption guardrails.
    """
    source = params if isinstance(params, dict) else {}
    return {key: source.get(key) is True for key in _CONFIRMATION_FLAGS}


def _stop_event_for(run_id):
    return _stop_events.setdefault(int(run_id), threading.Event())


def _staging_root() -> Path:
    # face_dataset_service has no DATA_DIR of its own (its image root is
    # cfg.dataset_images_root() = DATA_DIR/datasets); the actual data root
    # lives in config.py as the private _data_dir() (same convention already
    # used by services.chatgpt_oauth). cloud_runs is a sibling of datasets/.
    root = cfg._data_dir() / 'cloud_runs'
    root.mkdir(parents=True, exist_ok=True)
    return root


def get_active_runs():
    return (CloudTrainingRun.query
            .filter(CloudTrainingRun.status.in_(ACTIVE_STATES))
            .order_by(CloudTrainingRun.id.asc()).all())


def get_active_run():
    """Compat alias for single-run callers/tests: the first of the active
    runs (or None). Multi-run-aware code uses get_active_runs()."""
    actives = get_active_runs()
    return actives[0] if actives else None


def active_runs_for(dataset_id):
    """Non-terminal cloud runs of ONE dataset (empty list when none). Scoped
    twin of get_active_runs(); delete_dataset uses it to refuse deleting a
    dataset out from under a running pod."""
    return (CloudTrainingRun.query
            .filter_by(dataset_id=int(dataset_id))
            .filter(CloudTrainingRun.status.in_(ACTIVE_STATES))
            .order_by(CloudTrainingRun.id.asc()).all())


def _assert_official_base_reachable(repo_id, token, timeout=8):
    """Fail the launch when the account cannot actually download `repo_id`.

    Hugging Face answers **200 on the model's metadata** for a gated repo you have
    not been granted — only fetching a FILE returns 403. So this asks for the file
    listing under auth, which is subject to the same gate, and reads the status.

    FAIL-OPEN on anything that is not an outright refusal: a timeout, DNS failure or
    HF outage must never block a launch that would have worked. The pod remains the
    real authority; this only converts the ONE failure we can predict — a gate the
    user has never accepted — into a message that arrives before the bill."""
    if not repo_id:
        return
    import urllib.error
    import urllib.request
    req = urllib.request.Request(
        f'https://huggingface.co/api/models/{repo_id}/tree/main',
        headers={'Authorization': f'Bearer {token}'} if token else {})
    try:
        urllib.request.urlopen(req, timeout=timeout).read(1)
    except urllib.error.HTTPError as e:
        if e.code not in (401, 403):
            return                          # 404 / 5xx: not our call to make
        raise ValueError(
            f'Hugging Face refuses access to {repo_id}, which the rented GPU has to '
            f'download. Open https://huggingface.co/{repo_id} while signed in with '
            'the account your HF token belongs to, accept the licence ("Agree and '
            'access repository"), then launch again. Approval is usually instant. '
            'Nothing was rented, so this run cost nothing.') from None
    except Exception:                        # noqa: BLE001 — offline/outage: fail open
        return


def _assert_launch_guardrails(dataset_id, fam):
    """Raise when a cloud launch cannot reserve an active slot.

    Callers may use this once as a cheap fast-fail before expensive preflight,
    but the authoritative call must happen while ``_launch_reservation_lock``
    is held and immediately before inserting the ``preparing`` row.
    """
    actives = get_active_runs()
    limit = max(1, int((cfg.get('cloud.max_concurrent_runs') or 1)))
    # Uniqueness is per (dataset, family): a zimage run and a krea run may
    # train the same dataset in parallel. An active run whose family is
    # unknown (pre-feature row) blocks every family of its dataset, out of
    # caution.
    if any(r.dataset_id == dataset_id and (_run_family(r) or fam) == fam
           for r in actives):
        raise RuntimeError(f'this dataset already has an active {fam} cloud run')
    if len(actives) >= limit:
        raise RuntimeError(
            f'cloud run limit reached ({len(actives)}/{limit} active) — '
            'raise cloud.max_concurrent_runs in Settings')

    # Monthly budget: block LAUNCHES only — a running pod is NEVER killed
    # over budget (that would waste the money already spent on its training).
    budget = float(cfg.get('cloud.monthly_budget_usd') or 0)
    if budget > 0:
        spent = month_spend_usd()
        if spent >= budget:
            raise RuntimeError(
                f'monthly cloud budget reached (${spent:.2f} of ${budget:.2f}) — '
                'raise cloud.monthly_budget_usd in Settings')


def _run_param(run, key):
    """One key of the run's train_params JSON. None when the params are absent
    or corrupted — a pre-feature row, or the 'preparing' window before launch
    stamps them. Valid-but-non-dict JSON ('"x"', '[1]', '3') must degrade to
    None too, not AttributeError — one corrupt row would 500 cloud_status."""
    try:
        parsed = json.loads(run.train_params or '{}')
        return parsed.get(key) if isinstance(parsed, dict) else None
    except (ValueError, TypeError):
        return None


def _run_family(run):
    """Family ('zimage'/'krea'/...) stamped in the run's train_params."""
    return _run_param(run, 'train_type')


class _RunConfigDataset:
    """Read-only view of a dataset whose config inputs are forced to the values
    stamped for this run; every other attribute delegates to the real dataset.

    The cloud monitor builds the pod job through this view so the job's
    architecture/variant come from what the run was LAUNCHED with — never from
    the dataset's *current* row. Each launch persists ds.train_type /
    ds.train_variant (last writer wins) and the monitor rebuilds the config
    minutes later, at pod boot; a second launch on the same dataset (or a
    /train-type change) between this run's launch and its boot would otherwise
    retarget its architecture. Incident 2026-07-14: a Krea run launched first, a
    Z-Image run 28 min later persisted 'zimage', and the Krea pod — booting after
    that — would have been rebuilt as Z-Image under a Krea name (wrong arch on a
    rented GPU). build_job_config only READS the dataset, so a view is enough:
    no DB mutation, nothing to restore, and both concurrent runs stay isolated."""

    def __init__(self, ds, train_type, train_variant, train_base_model='',
                 train_settings_snapshot=_UNSET, train_slider_snapshot=_UNSET):
        self._ds = ds
        self._train_type = train_type
        self._train_variant = train_variant
        self._train_base_model = train_base_model
        self._train_settings_snapshot = train_settings_snapshot
        self._train_slider_snapshot = train_slider_snapshot

    @property
    def train_type(self):
        return (self._train_type if self._train_type is not None
                else getattr(self._ds, 'train_type', None))

    @property
    def train_variant(self):
        return (self._train_variant if self._train_variant is not None
                else getattr(self._ds, 'train_variant', None))

    @property
    def train_base_model(self):
        # Cloud runs always stamp their launch-time selection.  In particular,
        # an empty string means the official Hugging Face base and must not
        # fall through to a base subsequently persisted on the dataset row.
        return self._train_base_model

    @property
    def train_settings(self):
        # ``None`` is a meaningful snapshot: the run was launched with the
        # family defaults. Only _UNSET means a legacy run without a snapshot.
        return (getattr(self._ds, 'train_settings', None)
                if self._train_settings_snapshot is _UNSET
                else self._train_settings_snapshot)

    @property
    def train_slider(self):
        # Slider mode (Beta) is read off this column by build_job_config
        # (slider_mode_enabled -> _apply_slider_overrides). Frozen per run like
        # train_settings: ``None`` means "not a slider run at launch"; only
        # _UNSET (a legacy row that predates the snapshot) falls back to the
        # live dataset column. A @property is resolved by normal lookup, so it
        # deliberately shadows the __getattr__ delegation below.
        return (getattr(self._ds, 'train_slider', None)
                if self._train_slider_snapshot is _UNSET
                else self._train_slider_snapshot)

    def __getattr__(self, name):
        # Reached only for attributes not resolved normally (i.e. everything
        # except _ds / _train_* / the two properties) -> delegate to the real ds.
        return getattr(self._ds, name)


def _run_config_dataset(ds, params):
    """Wrap ``ds`` so build_job_config reads THIS run's stamped recipe.

    Advanced settings must be immutable per run: the pod job is built minutes
    after launch and an automatic retry even later. Dataset edits in between
    affect future launches only. Legacy rows without a settings snapshot retain
    their historical DB fallback.
    """
    fam = params.get('train_type')
    var = params.get('variant')
    base = params.get('base_model', '')
    advanced = params.get(_TRAIN_SETTINGS_SNAPSHOT, _UNSET)
    slider = params.get(_TRAIN_SLIDER_SNAPSHOT, _UNSET)
    return _RunConfigDataset(ds, fam, var, base, advanced, slider)


def _recipe_replay_diagnostic(params):
    """Safety diagnosis for retry/continue without mutating the source run."""
    if not isinstance(params, dict):
        return None
    return lt.zimage_recipe_diagnostic(
        params.get('train_type'), params.get('variant'),
        params.get('effective_base'), params.get('training_adapter'),
        params.get('recipe_version'))


def _assert_recipe_replayable(params, action):
    diag = _recipe_replay_diagnostic(params)
    if diag and diag.get('status') in ('legacy_incompatible', 'incompatible'):
        raise ValueError(
            f'cannot {action} this run safely: {diag.get("warning")} Start a fresh '
            'run with the validated Z-Image recipe instead.')


def latest_run_for(dataset_id, train_type=None):
    """Newest run of the dataset; with train_type, the newest run OF THAT
    FAMILY. Falls back to the plain newest when none matches (or the filter
    is absent) so rows without a stamped family stay reachable."""
    q = (CloudTrainingRun.query.filter_by(dataset_id=dataset_id)
         .order_by(CloudTrainingRun.id.desc()))
    newest = q.first()
    if not train_type:
        return newest
    fam = fds.normalize_train_type(train_type)
    for r in q.all():
        if _run_family(r) == fam:
            return r
    return newest


# A monitor state write that loses a race for the SQLite write lock must not
# kill a run that is burning rented GPU time. The DB is opened WAL with
# busy_timeout=5000 (app/__init__.py), so a writer only ever sees 'database is
# locked' when another writer held the lock for more than five seconds — a
# captioning batch, a bank import, a big dataset write. That happened on
# 2026-07-26: two monitors had just created their job on the pod and died on
# `_set(status='training')` with `sqlite3.OperationalError: database is locked`,
# three minutes into runs that then sat abandoned for an hour of paid 5090 time
# (runs #106 and #107). The lock is transient by nature, so the commit is
# retried instead of being fatal.
_COMMIT_RETRIES = 4
_COMMIT_RETRY_BASE_SECONDS = 0.5


def _is_locked_error(exc):
    return 'database is locked' in str(exc).lower()


def _set(run, **fields):
    """Write monitor state, surviving a transient SQLite write-lock loss.

    A failed commit leaves the session with a pending rollback and — once
    rolled back — the instance reverted to its stored values, so the fields are
    re-applied on every attempt rather than set once up front.

    Rolling back is therefore the FIRST thing the failure path does, before
    anything reads the instance and before the raise. Until a rollback happens,
    the session refuses every operation with PendingRollbackError, and a
    persistent instance whose attributes were expired by the previous commit
    cannot even be read: touching `run.id` fires a lazy load, which needs the
    session, which raises. That is not theoretical — it defeated this very
    retry loop on 2026-07-28. The lock was hit, the failure path formatted its
    log line, reading `run.id` raised PendingRollbackError out of _set, and the
    monitor thread died in the exact way the retry was written to prevent. Run
    #121 then sat at 'training' with no error and a live rented 5090, because
    the caller's recovery path (_finish) inherited the same poisoned session and
    failed too. The run id is read up front, off the healthy session, so the
    log line cannot resurrect that failure."""
    run_id = getattr(run, 'id', '?')
    for attempt in range(_COMMIT_RETRIES):
        for k, v in fields.items():
            setattr(run, k, v)
        run.updated_at = datetime.utcnow()
        try:
            db.session.commit()
            return
        except Exception as e:                    # noqa: BLE001 - re-raised below
            db.session.rollback()
            if attempt == _COMMIT_RETRIES - 1 or not _is_locked_error(e):
                raise
            logger.warning('run %s: SQLite write lock busy (attempt %s/%s) — '
                           'retrying the state write', run_id,
                           attempt + 1, _COMMIT_RETRIES)
            _sleep(_COMMIT_RETRY_BASE_SECONDS * (2 ** attempt))


def _reconcile_before_launch(app):
    """Seam around the launch-time reconcile_orphans() call (defined below).
    A thin indirection rather than calling reconcile_orphans directly so
    tests can no-op launch's reconcile call without also neutering tests
    that exercise reconcile_orphans() itself -- both are the same module-level
    name, so patching that name would silence both call sites at once."""
    reconcile_orphans(app)


def retry_cloud_run(user_id, run_id) -> dict:
    """Relance un run TERMINÉ EN ERREUR avec les paramètres exacts persistés au
    lancement d'origine (train_params) — le bouton ↻ Retry de la page Cloud.
    C'est un VRAI launch_cloud_training (pod frais, mêmes garde-fous : limite
    de runs actifs, budget, unicité par famille), pas une réanimation du pod
    mort. Les confirmations ne sont rejouées que si le lancement d'origine les
    avait explicitement enregistrées."""
    run = db.session.get(CloudTrainingRun, int(run_id))
    if not run:
        raise ValueError('unknown cloud run')
    if run.status != 'error':
        raise ValueError('only a failed run can be retried')
    try:
        p = json.loads(run.train_params or '{}')
    except ValueError:
        p = {}
    if not isinstance(p, dict):
        p = {}
    _assert_recipe_replayable(p, 'retry')
    return launch_cloud_training(
        user_id, run.dataset_id,
        steps=p.get('steps'),
        base_model=p.get('base_model', ''),
        variant=p.get('variant'),
        train_type=p.get('train_type'),
        masked=p.get('masked', True),
        **_confirmation_flags(p),
        gpu_name=p.get('requested_gpu'),
        resume_ckpt_path=p.get('resume_ckpt_path'),
        resume_step=p.get('resume_step'),
        train_settings_snapshot=p.get(_TRAIN_SETTINGS_SNAPSHOT, _UNSET),
        train_slider_snapshot=p.get(_TRAIN_SLIDER_SNAPSHOT, _UNSET))


def _run_staging_checkpoints(run) -> list:
    """This run's HARVESTED checkpoints that still live in staging (NOT the
    trash — trashed saves are moved out of staging_dir): list of
    {'filename', 'step', 'path'}, step-sorted ascending. Mirrors
    cloud_checkpoints' step extraction so 'continue' resumes from the exact same
    checkpoint the hub lists. The unsuffixed FINAL save (no _<step> suffix) is
    the run's target step count."""
    sd = run.staging_dir
    if not sd or not os.path.isdir(sd):
        return []
    target = int(_run_param(run, 'steps') or 0)
    out = []
    for name in os.listdir(sd):
        if not name.lower().endswith('.safetensors'):
            continue
        m = re.search(r'_(\d{6,})\.safetensors$', name)
        out.append({'filename': name,
                    'step': int(m.group(1)) if m else target,
                    'path': os.path.join(sd, name)})
    # step asc; a suffixed save wins ties over the unsuffixed final (deterministic).
    out.sort(key=lambda e: (e['step'], bool(re.search(r'_(\d{6,})\.safetensors$',
                                                       e['filename']))))
    return out


def _merge_resume_overrides(snapshot, patch):
    """Fold a validated safe-override patch into a per-run train_settings snapshot
    (JSON string, None, or _UNSET) for a cloud continue. Mirrors the local path,
    where update_train_settings persists the same keys — but a cloud run carries a
    frozen snapshot instead of the live dataset column, so we merge into a COPY and
    never touch the dataset. A None value drops the key (reset to default), matching
    update_train_settings' semantics. Returns a JSON string (or None if empty)."""
    if snapshot in (_UNSET, None):
        base = {}
    else:
        try:
            base = json.loads(snapshot)
        except (ValueError, TypeError):
            base = {}
        if not isinstance(base, dict):
            base = {}
    for k, v in patch.items():
        if v is None:
            base.pop(k, None)
        else:
            base[k] = v
    return json.dumps(base) if base else None


def continue_cloud_run(user_id, run_id, extra_steps=1000, from_step=None,
                       overrides=None) -> dict:
    """Reprend un run cloud TERMINAL (done OU en échec) depuis un checkpoint
    harvesté et vise step_de_reprise + extra_steps — le pendant cloud de
    lora_training.continue_training. C'est un VRAI launch_cloud_training (pod
    frais, mêmes garde-fous : limite de runs actifs, budget, unicité par
    famille) avec les paramètres persistés du run source (variante/famille/
    masked/GPU class, comme retry_cloud_run) ; son monitor, AVANT de démarrer le
    job, dépose le checkpoint dans le save_root du job sur le pod pour déclencher
    l'auto-resume d'ai-toolkit.

    ``from_step`` absent → dernier checkpoint (défaut). Fourni → CE step précis, y
    compris un checkpoint plus ancien : le seed d'un checkpoint arbitraire sur un
    pod NEUF est le même canal que le seed du dernier, et le staging du run source
    n'est jamais touché — repartir d'un step inférieur est donc gratuit côté cloud.
    ``overrides`` = mêmes réglages sûrs que le local (cadence/preview prompts),
    fusionnés dans le snapshot du run (jamais dans le dataset). register_launch
    reste un launch cloud normal — le resume est un détail d'exécution."""
    run = db.session.get(CloudTrainingRun, int(run_id))
    if not run:
        raise ValueError('unknown cloud run')
    # Continue from any TERMINAL run — a run that failed at pod teardown
    # ('pod did not become ready in time') can still have harvested, complete
    # checkpoints in its staging, and resuming from one is valid. Only a run
    # that is STILL RUNNING is blocked; the `no harvested checkpoint` check
    # below is the real gate for a terminal run whose staging was cleaned.
    if run.status in ACTIVE_STATES:
        raise ValueError('a run that is still running cannot be continued — '
                         'wait for it to finish or fail')
    try:
        p = json.loads(run.train_params or '{}')
    except ValueError:
        p = {}
    if not isinstance(p, dict):
        p = {}
    _assert_recipe_replayable(p, 'continue')
    override_patch = lt.validate_resume_overrides(overrides)
    cks = _run_staging_checkpoints(run)
    if not cks:
        raise ValueError('no harvested checkpoint to continue from — its staging '
                         'was cleaned; relaunch a fresh cloud run instead')
    # Which harvested checkpoint to resume from. Default = the latest; a specific
    # step restarts from an earlier epoch (seeding it onto the fresh pod is the same
    # channel, and the source run's staging is read-only here — nothing destroyed).
    if from_step is None:
        chosen = cks[-1]
    else:
        try:
            want = int(from_step)
        except (TypeError, ValueError):
            raise ValueError('from_step must be an integer step')
        matches = [c for c in cks if c['step'] == want]
        if not matches:
            avail = sorted({c['step'] for c in cks})
            raise ValueError(
                f'no harvested checkpoint at step {want} for this run (available: {avail})')
        # Prefer a suffixed save over the unsuffixed final when steps tie.
        chosen = min(matches, key=lambda c: not re.search(
            r'_(\d{6,})\.safetensors$', c['filename']))
    try:
        extra = max(100, int(extra_steps))
    except (TypeError, ValueError):
        extra = 1000
    snapshot = p.get(_TRAIN_SETTINGS_SNAPSHOT, _UNSET)
    # Resolve the LR factor against the SOURCE run's frozen settings (never the live
    # dataset): a 1e-4 run continues at 5e-5 / 1e-5. Refused loudly on a Prodigy run
    # before any launch. The resulting learning_rate merges into the per-run snapshot
    # exactly like cadence/timestep — the pod's _lr_eff then reads it.
    lr_factor = override_patch.pop('lr_factor', None)
    if lr_factor is not None:
        run_settings = {}
        if snapshot not in (_UNSET, None):
            try:
                parsed = json.loads(snapshot)
                run_settings = parsed if isinstance(parsed, dict) else {}
            except (ValueError, TypeError):
                run_settings = {}
        override_patch['learning_rate'] = lt.resolve_resume_lr(run_settings, lr_factor)
    if override_patch:
        snapshot = _merge_resume_overrides(snapshot, override_patch)
    # Lineage: the parent is the provenance record of the cloud run being
    # continued (source-of-truth edge for the Runs-hub tree). Legacy cloud runs
    # that predate the registry have no record -> the child is a root (NULL).
    from ..models import TrainingRunRecord
    _parent = (TrainingRunRecord.query
               .filter_by(cloud_run_id=run.id)
               .order_by(TrainingRunRecord.id.desc()).first())
    res = launch_cloud_training(
        user_id, run.dataset_id,
        steps=chosen['step'] + extra,
        base_model=p.get('base_model', ''),
        variant=p.get('variant'),
        train_type=p.get('train_type'),
        masked=p.get('masked', True),
        **_confirmation_flags(p),
        gpu_name=p.get('requested_gpu'),
        resume_ckpt_path=chosen['path'], resume_step=chosen['step'],
        train_settings_snapshot=snapshot,
        train_slider_snapshot=p.get(_TRAIN_SLIDER_SNAPSHOT, _UNSET),
        parent_record_id=(_parent.id if _parent else None),
        resumed_from=chosen['step'])
    res['resumed_from'] = chosen['step']
    res['target_steps'] = chosen['step'] + extra
    return res


def continue_local_run_in_cloud(user_id, dataset_id, extra_steps=1000,
                                from_step=None, overrides=None,
                                base_model=_UNSET, variant=None, train_type=None,
                                masked=True, allow_caption_mismatch=False,
                                allow_uncaptioned=False, allow_caption_quality=False,
                                allow_unverified_weights=False, allow_not_ready=False,
                                gpu_name=None) -> dict:
    """▶ Continue a LOCAL run's checkpoint IN THE CLOUD — the mirror of
    continue_cloud_run, and the other half of "pick your lane" in the ▶ Continue
    dialog. Nothing new is invented: the pod-side resume is the SAME seam
    (`resume_ckpt_path`), which launch_cloud_training's monitor drops into the
    job's save_root on a FRESH pod before start_job so ai-toolkit auto-resumes
    from it. The only difference with the cloud→cloud continue is where the file
    comes from: this one reads the ai-toolkit RUN DIR on disk instead of a cloud
    run's harvested staging.

    ``from_step`` absent → the newest local save. Provided → THAT step, including
    an earlier epoch: unlike the local lane (which archives the run aside and
    re-seeds it), seeding an arbitrary checkpoint onto a fresh pod touches
    NOTHING on disk — the local run dir is read-only here.

    Every guard of a normal cloud launch applies unchanged (vast.ai key, budget,
    active-run limit, per-family uniqueness, dataset export/captions): this IS a
    launch_cloud_training call, the resume is an execution detail. ``overrides``
    = the same safe subset as everywhere (cadence / preview prompts / timestep /
    lr_factor), merged into THIS run's settings snapshot — the dataset's own
    persisted settings are never touched (the local lane's update_train_settings
    is a local-lane behaviour, not something to replicate on a cloud launch)."""
    ds = fds.get_dataset(user_id, dataset_id)
    if not ds:
        raise ValueError('dataset not found')
    fam = lt._train_type(ds, train_type)
    var = variant or getattr(ds, 'train_variant', None) or lt._default_variant_for(fam)
    # base_model _UNSET = the dataset's persisted base (the queue's behaviour);
    # an explicit value (the UI's checkpoint selection) targets THAT lane.
    lane = {} if base_model is _UNSET else {'base_model': base_model}
    base = (getattr(ds, 'train_base_model', None) or '') if base_model is _UNSET \
        else (base_model or '')
    # Validate the safe-subset overrides BEFORE anything else — a forbidden key
    # must fail with nothing launched (same contract as both other lanes).
    override_patch = lt.validate_resume_overrides(overrides)
    # The run dir lives under ai-toolkit's output: without it configured there is
    # no local save to send anywhere. Say that, rather than leaking the raw
    # 'ai-toolkit is not configured' from a lane the user asked to run in the CLOUD.
    try:
        cks = lt.list_checkpoints(user_id, dataset_id, family=fam, variant=var, **lane)
    except RuntimeError:
        raise ValueError('no local checkpoint to continue from — ai-toolkit is not '
                         'configured, so this machine has no local run folder')
    if not cks:
        raise ValueError('no local checkpoint to continue from for this base — '
                         'the run folder holds no save (a cloud run\'s epochs '
                         'live in its own staging: continue THAT run instead)')
    if from_step is None:
        chosen = cks[-1]
    else:
        try:
            want = int(from_step)
        except (TypeError, ValueError):
            raise ValueError('from_step must be an integer step')
        matches = [c for c in cks if c['step'] == want]
        if not matches:
            avail = sorted({c['step'] for c in cks})
            raise ValueError(
                f'no local checkpoint at step {want} for this run (available: {avail})')
        # Ties (a numbered save and the bare final at the same step): prefer the
        # numbered file — same rule as the local lane.
        chosen = min(matches, key=lambda c: bool(c.get('final')))
    # Resolve through the whitelisting helper (never os.path.join on a name from
    # the wire): it only returns a path that IS a save of this exact run.
    path = lt.checkpoint_file_path(user_id, dataset_id, chosen['filename'],
                                   family=fam, variant=var, **lane)
    if not path:
        raise ValueError(f"local checkpoint '{chosen['filename']}' is no longer on disk")
    try:
        extra = max(100, int(extra_steps))
    except (TypeError, ValueError):
        extra = 1000
    # LR factor → an absolute rate, resolved against the DATASET's live settings
    # (a local run trains from those, there is no per-run snapshot), and refused
    # loudly on a Prodigy run before any launch.
    lr_factor = override_patch.pop('lr_factor', None)
    if lr_factor is not None:
        override_patch['learning_rate'] = lt.resolve_resume_lr(lt._train_settings(ds), lr_factor)
    # Lineage: the parent is the record that PRODUCED the file being seeded — the
    # `record_id` list_checkpoints stamps on every save — NOT the newest record of
    # the lane. A lane holds several runs whose saves share one run dir, so "newest
    # record" pointed the edge at a run whose weights were never loaded: the graph
    # claimed a continuation of a rank-32 run while a rank-64 file went up the wire.
    # Falls back to the lane's newest record for a pre-registry save. Best-effort —
    # a failure leaves the edge NULL and never blocks the launch.
    from . import checkpoint_registry
    try:
        _parent = checkpoint_registry.record_by_id(chosen.get('record_id'))
        if _parent is None:
            _parent = checkpoint_registry.newest_record_for(dataset_id, fam, base, var)
    except Exception:
        _parent = None
    # The LoRA's geometry belongs to the weights, not to today's dataset settings:
    # rank-32 weights cannot load into a rank-64 network. Without this, a resume
    # stamped the dataset's LIVE rank onto the run (snapshot _UNSET) — edit rank
    # between two runs and the "continuation" silently trained a different LoRA.
    # This lane carries a PER-RUN snapshot, so the parent's geometry is inherited
    # here with no side effect on the dataset (the local lane, which trains from
    # the persisted settings, refuses loudly instead).
    geometry = checkpoint_registry.network_geometry(_parent)
    snapshot = _UNSET      # _UNSET → launch stamps the dataset's live settings
    if override_patch or geometry:
        snapshot = _merge_resume_overrides(getattr(ds, 'train_settings', None),
                                           {**override_patch, **geometry})
    res = launch_cloud_training(
        user_id, dataset_id,
        steps=chosen['step'] + extra,
        base_model=base, variant=var, train_type=fam, masked=masked,
        allow_caption_mismatch=allow_caption_mismatch,
        allow_uncaptioned=allow_uncaptioned,
        allow_caption_quality=allow_caption_quality,
        allow_unverified_weights=allow_unverified_weights,
        allow_not_ready=allow_not_ready,
        gpu_name=gpu_name,
        resume_ckpt_path=path, resume_step=chosen['step'],
        train_settings_snapshot=snapshot,
        parent_record_id=(_parent.id if _parent else None),
        resumed_from=chosen['step'])
    res['resumed_from'] = chosen['step']
    res['target_steps'] = chosen['step'] + extra
    return res


def launch_cloud_training(user_id, dataset_id, steps=None, base_model=_UNSET,
                          variant=None, train_type=None, masked=True,
                          allow_caption_mismatch=False, allow_uncaptioned=False,
                          allow_caption_quality=False,
                          allow_unverified_weights=False, allow_not_ready=False,
                          gpu_name=None, resume_ckpt_path=None, resume_step=None,
                          auto_retry_count=0, auto_retry_of=None,
                          strict_gpu=False, train_settings_snapshot=_UNSET,
                          train_slider_snapshot=_UNSET,
                          parent_record_id=None, resumed_from=None) -> dict:
    if not cfg.secret('VAST_API_KEY'):
        raise RuntimeError('vast.ai API key is not configured — add it in Settings')
    # A user launching after days away is exactly when an expired
    # error_pod_kept pod (past its recovery window) should be reaped, not
    # just at boot. reconcile_orphans() never raises, so this is safe; routed
    # through the _reconcile_before_launch seam (rather than calling
    # reconcile_orphans directly) so tests can no-op *this* call site without
    # also neutering tests that exercise reconcile_orphans() itself.
    from flask import current_app
    # Fire-and-forget: reconcile_orphans never raises and reaping an expired
    # pod does not need to finish before THIS launch — inline it cost the
    # launch click a vast list_instances round-trip.
    threading.Thread(
        target=_reconcile_before_launch,
        args=(current_app._get_current_object(),), daemon=True,
        name='cloud-reconcile-prelaunch').start()
    ds = fds.get_dataset(user_id, dataset_id)
    if not ds:
        raise ValueError('dataset not found')
    # Slider LoRA mode (Beta) rides the SAME pod as every other family: the
    # pod's ai-toolkit registers `concept_slider` as a built-in trainer uid
    # (extends DiffusionTrainer — the very path _cloudify_job_config targets),
    # build_job_config already emits the full concept_slider process for the
    # cloud families, and the prompt-pair/substrate preflight below is family-
    # agnostic. The launch-time slider settings are frozen into the run params
    # (train_slider snapshot) exactly like train_settings, so a later toggle or
    # prompt edit cannot retarget an in-flight run.
    fam = fds.normalize_train_type(train_type or getattr(ds, 'train_type', None))
    # ``base_model`` is an explicit launch selection on the HTTP path.  Keep a
    # compatibility fallback for older internal callers that omitted it: use
    # the persisted value only while staying on the dataset's persisted family.
    # If the caller explicitly switches family, that old value belongs to the
    # previous family and must not make an official Krea/Klein launch fail.
    if base_model is _UNSET:
        persisted_fam = fds.normalize_train_type(getattr(ds, 'train_type', None))
        selected_base = (getattr(ds, 'train_base_model', None)
                         if not train_type or fam == persisted_fam else '')
    else:
        selected_base = base_model
    base_model = str(selected_base or '').strip()
    # Custom weights ride the cloud through a PRIVATE Hugging Face repo on the
    # user's account (one-time push, hf_base_push) — but only for the three
    # cloud families. Everything else keeps the historical refusal verbatim.
    from . import hf_base_push
    if base_model and fam not in hf_base_push.CLOUD_CUSTOM_BASE_FAMILIES:
        raise ValueError('custom weights are local-only — cloud training '
                         'uses the official Hugging Face bases')
    # These fields are local-only.  Unlike ``train_base_model`` they have no
    # supported cloud-family meaning (SDXL itself is rejected below), so retain
    # the historical fail-fast instead of silently accepting a selected override.
    if getattr(ds, 'train_vae_path', None) or getattr(ds, 'train_te_path', None):
        raise ValueError('custom VAE/text-encoder overrides are local-only — '
                         'cloud training uses the official Hugging Face bases')
    if fam == 'sdxl':
        raise ValueError('SDXL training needs a local base checkpoint — '
                         'cloud training supports Z-Image, Krea and FLUX.2 Klein')
    # flux2klein n'est PAS bloqué (contrairement à flux) : ses bases sont des repos
    # HF officiels que le pod télécharge lui-même — le 9B (32-48 GB VRAM) est même
    # la voie cloud principale de la famille.
    if fam == 'flux':
        raise ValueError('FLUX.1 training is local-only for now — '
                         'cloud training supports Z-Image, Krea and FLUX.2 Klein')
    # Anima is LOCAL-ONLY for this wave: a pod would need ai-toolkit with the
    # 'anima' arch (PR #860, 2026-07-15) + a recent diffusers, which current pod
    # images predate — renting one would burn a GPU on an unknown arch. Refuse
    # BEFORE any reservation. Lift once the pod image is verified.
    if fam == 'anima':
        raise ValueError('Anima cloud training is coming once the pod image is '
                         'verified — train it locally for now')
    variant = (variant or '').strip().lower()
    confirmations = {
        'allow_caption_mismatch': bool(allow_caption_mismatch),
        'allow_uncaptioned': bool(allow_uncaptioned),
        'allow_caption_quality': bool(allow_caption_quality),
        'allow_unverified_weights': bool(allow_unverified_weights),
        'allow_not_ready': bool(allow_not_ready),
    }
    recipe = None
    if fam == 'zimage':
        # Authoritative recipe validation happens before the reservation row and
        # therefore before a monitor can provision/rent a GPU.  build_job_config
        # validates again when the pod job is assembled. A custom base resolves
        # to the custom recipe (extras from the official Turbo pipeline), same
        # as the local path.
        recipe = lt.zimage_training_recipe(
            variant or lt._default_variant_for(fam), base_model=base_model or None)
        variant = recipe['variant']
    elif variant not in lt._valid_variants_for(fam):
        variant = lt._default_variant_for(fam)
    # Custom base: local-parity guardrails first (the confirmable arch sniff on
    # a still-present file; the distillation confirm for a custom Z-Image
    # declared Base/De-Turbo), then the pre-rent repo check — the pod downloads
    # the base from a PRIVATE repo on the user's HF account (hf_base_push), so
    # the launch fails HERE, with an actionable message, never after renting.
    base_repo = None
    if base_model:
        if fam == 'zimage':
            lt.assert_zimage_custom_recipe_confirmed(
                fam, base_model, variant, allow_unverified_weights)
        elif os.path.isfile(base_model):
            lt.preflight_custom_paths(
                fam, weights=base_model,
                allow_unverified_weights=allow_unverified_weights)
        base_repo = hf_base_push.require_base_repo(
            ds, fam, variant, base_model, cfg.secret('HF_TOKEN'))
    else:
        # OFFICIAL base: the pod downloads it from Hugging Face. Several are GATED
        # (Krea, FLUX, FLUX.2 Klein) and a gate the account never accepted answers
        # 403 — on the pod, after renting. Three runs were paid for and lost that
        # way, and the card only showed "403 Client Error (Request ID…)", hiding the
        # sentence that named the repo. One HEAD here costs nothing and turns that
        # into a message before a GPU is reserved.
        _assert_official_base_reachable(
            lt.official_base_repo(ds, fam, variant), cfg.secret('HF_TOKEN'))
    # Cheap fast-fail before the image/caption preflight below. This read is
    # intentionally advisory: another Flask request can reserve a slot after
    # it, so the same checks are repeated atomically at reservation time.
    _assert_launch_guardrails(dataset_id, fam)

    # Same caption-mismatch preflight as launch_training (MISMATCH_CAPTION
    # contract): assert_trainable is ALREADY a standalone helper in
    # lora_training.py (called from launch_training, not inlined there), so
    # no extraction was needed -- just match its real signature:
    # assert_trainable(dataset_id, train_type=None, allow_caption_mismatch=False).
    lt.assert_trainable(dataset_id, train_type=fam,
                        allow_caption_mismatch=allow_caption_mismatch,
                        allow_uncaptioned=allow_uncaptioned,
                        allow_caption_quality=allow_caption_quality,
                        allow_not_ready=allow_not_ready,
                        variant=variant)

    # The explicit launch base (''=official) rides into the run name so a
    # custom-base run keeps its own folder/prefix (combo-hash suffix, exactly
    # like local runs) and Base/De-Turbo cannot share Turbo's run path.
    run_name = lt._run_name(ds, base_model=base_model, family=fam, variant=variant)
    # Freeze the dataset (manifest + caption text + image content hashes +
    # environment) BEFORE the reservation lock, exactly like the local path: the
    # only file I/O of the registration happens here, so the registration itself
    # stays one short write and neither the reservation window nor the launch
    # response grows a second writer competing for the database lock.
    from . import checkpoint_registry
    _prepared = checkpoint_registry.prepare_launch(
        user_id, dataset_id, base_model=base_model)
    with _launch_reservation_lock:
        # Authoritative re-check + insert. Keeping the commit inside this
        # process-wide critical section means a second request always sees the
        # first request's preparing row before it can reserve or rent a pod.
        _assert_launch_guardrails(dataset_id, fam)
        run = CloudTrainingRun(
            dataset_id=dataset_id, status='preparing', run_name=run_name,
            # Stamp the family in the reservation itself. Without this, the
            # short window before the complete params are saved would make a
            # legitimate second-family launch look like an unknown-family run.
            train_params=json.dumps({'train_type': fam, 'variant': variant,
                                     'base_model': base_model, **confirmations}))
        db.session.add(run)
        db.session.commit()
    try:
        # Anything failing past this point (params, thread start) must not
        # strand the 'preparing' row forever — that would deadlock the
        # single-active-run guard above. Flip it to 'error' and re-raise.
        # NOTE: the heavy dataset EXPORT (rembg masks: ~1-2 s/image) happens in
        # the MONITOR thread (_prepare_staging), not here — this call must
        # return in well under a second or the launch dialog sits on
        # 'Launching…' for a minute (user-observed).
        _set(run, vast_label=f'lds-{run.id}',
             job_name=f'lds{run.id}_{run_name}')
        # Mirror the LOCAL launch: persist this dataset's family/variant as its
        # remembered selection (launch_training does the same; two launch tests
        # assert it). This is now ONLY the dataset's default selection — the
        # monitor builds the pod job from the run's STAMPED params (see
        # _run_config_dataset at the build site), so a later launch overwriting
        # this row can no longer retarget an already-provisioning run's arch.
        ds.train_type = fam
        ds.train_variant = variant
        db.session.commit()
        # Same floor as the local path — a sub-500 target produces a run with
        # zero usable snapshots.
        n_steps = (max(500, int(steps)) if steps else lt.default_steps(
            ds, train_type=fam, variant=variant))
        # requested_gpu (from the launch-time speed picker) is a PREFERENCE, not
        # a lock: _provision re-searches live offers and rents the cheapest one
        # of this class, falling back to the cheapest overall if the class has
        # since sold out (vast offers are ephemeral).
        params = {'steps': n_steps, 'variant': variant, 'base_model': base_model,
                  'train_type': fam, 'masked': bool(masked), **confirmations}
        if base_repo:
            # The monitor's rebuild (and any retry/continue replay) must route
            # the pod's name_or_path to the PRIVATE repo without recomputing
            # anything: stamp the repo id and the remote weight size (drives
            # the pod's disk_gb sizing in _provision).
            params['base_repo_id'] = base_repo['repo_id']
            params['base_size_bytes'] = int(base_repo.get('size_bytes') or 0)
        if recipe:
            params.update({'recipe_version': recipe['recipe_version'],
                           'effective_base': recipe['effective_base'],
                           'training_adapter': recipe['training_adapter']})
        # Freeze the RAW JSON, not only the compact provenance summary: it also
        # carries custom preview prompts and explicit family defaults. ``None``
        # deliberately means "family defaults at launch".
        if train_settings_snapshot is _UNSET:
            train_settings_snapshot = getattr(ds, 'train_settings', None)
        params[_TRAIN_SETTINGS_SNAPSHOT] = train_settings_snapshot
        # Freeze the slider column the same way: a fresh launch snapshots the
        # dataset's current train_slider blob; retry/continue replay the source
        # run's snapshot (passed in) so a slider run stays a slider run even if
        # the dataset's mode was toggled off in between. ``None`` = not a slider
        # run at launch (build_job_config then emits the normal process).
        if train_slider_snapshot is _UNSET:
            train_slider_snapshot = getattr(ds, 'train_slider', None)
        params[_TRAIN_SLIDER_SNAPSHOT] = train_slider_snapshot
        if gpu_name:
            params['requested_gpu'] = str(gpu_name)
        if auto_retry_count:
            params['auto_retry_count'] = max(0, int(auto_retry_count))
        if auto_retry_of is not None:
            params['auto_retry_of'] = int(auto_retry_of)
        if strict_gpu:
            params['strict_gpu'] = True
        # Continue-in-cloud: the monitor seeds this checkpoint into the pod job's
        # save_root before start_job so ai-toolkit auto-resumes from it. Absent
        # on a normal launch (the seed step is then a no-op).
        if resume_ckpt_path:
            params['resume_ckpt_path'] = str(resume_ckpt_path)
            if resume_step is not None:
                params['resume_step'] = int(resume_step)
        # Provenance registry (same as local launches): dataset version at
        # launch time, stamped into the params so payloads can expose it.
        rec = checkpoint_registry.register_launch(
            user_id, dataset_id, family=fam, source='cloud',
            variant=variant, masked=bool(masked), steps=n_steps,
            cloud_run_id=run.id,
            settings=lt.launch_settings_snapshot(
                _run_config_dataset(ds, params), fam),
            prepared=_prepared,
            parent_record_id=parent_record_id, resumed_from=resumed_from)
        if rec is not None:
            params['version'] = rec.version
        _set(run, train_params=json.dumps(params))
        _stop_event_for(run.id).clear()
        _start_monitor(run.id)
    except Exception as e:
        _set(run, status='error', error=f'launch failed: {e}',
             finished_at=datetime.utcnow())
        raise
    return {'run_id': run.id, 'status': run.status,
            'job_name': run.job_name, 'steps': n_steps}


_AUTO_RETRY_LIMIT = 1
_AUTO_RETRY_MARKERS = (
    'pod did not become ready',
    'pod unreachable',
    'connection aborted',
    'connection reset',
    'connectionreseterror',
    'remote end closed connection',
    'failed to establish a new connection',
    'max retries exceeded',
    'read timed out',
    'readtimeout',
    'connect timeout',
    'connecttimeout',
    'connection refused',
    'connectionrefusederror',
)


def _is_retryable_pod_failure(error) -> bool:
    """True only for transient pod/transport failures worth paying to retry."""
    text = str(error or '').lower()
    return any(marker in text for marker in _AUTO_RETRY_MARKERS)


_TRANSIENT_CREATE_CODES = ('400', '408', '409', '429', '500', '502', '503', '504')


def _is_transient_create_error(err) -> bool:
    """A vast create_instance refusal worth retrying with a FRESH offer: the
    offer was just taken (vast answers 400/409 — run #80's 'HTTP 400 {}'), a
    rate limit (429), or a vast-side hiccup (5xx). NOT an auth/quota rejection
    (401/403) or a genuinely-missing offer (404) that a retry cannot fix."""
    m = re.search(r'HTTP\s+(\d{3})', str(err or ''))
    return bool(m and m.group(1) in _TRANSIENT_CREATE_CODES)


def _auto_retry_child(parent_id):
    """Existing child, including the crash window before its id reached parent."""
    for child in CloudTrainingRun.query.order_by(CloudTrainingRun.id.desc()).all():
        if _run_param(child, 'auto_retry_of') == int(parent_id):
            return child
    return None


def _maybe_auto_retry(run, error):
    """Rent at most one fresh pod after a transient failure of an existing pod."""
    if (run.status != 'error' or not run.vast_instance_id
            or not _is_retryable_pod_failure(error)):
        return None

    with _auto_retry_lock:
        db.session.refresh(run)
        try:
            params = json.loads(run.train_params or '{}')
        except (TypeError, ValueError):
            return None
        if not isinstance(params, dict):
            return None
        replay_diag = _recipe_replay_diagnostic(params)
        if replay_diag and replay_diag.get('status') in (
                'legacy_incompatible', 'incompatible'):
            logger.warning('automatic retry blocked for unsafe legacy recipe on run %s',
                           run.id)
            return None
        try:
            retry_count = max(0, int(params.get('auto_retry_count') or 0))
        except (TypeError, ValueError):
            return None

        existing = _auto_retry_child(run.id)
        if existing is not None:
            params['auto_retry_scheduled'] = True
            params['auto_retry_pending'] = False
            params['auto_retry_run_id'] = existing.id
            _set(run, train_params=json.dumps(params),
                 phase_detail='Run failed — automatic retry launched')
            return {'run_id': existing.id, 'status': existing.status}

        pending_recovery = bool(params.get('auto_retry_scheduled')
                                and params.get('auto_retry_pending'))
        if retry_count >= _AUTO_RETRY_LIMIT:
            return None
        if params.get('auto_retry_scheduled') and not pending_recovery:
            return None

        # Commit the claim before renting. boot_recover resumes this exact
        # pending state if the app stops between the claim and child creation.
        params['auto_retry_scheduled'] = True
        params['auto_retry_pending'] = True
        _set(run, train_params=json.dumps(params),
             phase_detail='Run failed — automatic retry starting…')

        # Reuse the GPU class actually rented. requested_gpu may have fallen
        # back on the initial launch, so it is not necessarily the effective GPU.
        gpu_name = run.gpu_name or params.get('requested_gpu')
        try:
            result = launch_cloud_training(
                'local', run.dataset_id,
                steps=params.get('steps'),
                base_model=params.get('base_model', ''),
                variant=params.get('variant'),
                train_type=params.get('train_type'),
                masked=params.get('masked', True),
                **_confirmation_flags(params),
                gpu_name=gpu_name,
                resume_ckpt_path=params.get('resume_ckpt_path'),
                resume_step=params.get('resume_step'),
                auto_retry_count=retry_count + 1,
                auto_retry_of=run.id,
                strict_gpu=bool(gpu_name),
                train_settings_snapshot=params.get(
                    _TRAIN_SETTINGS_SNAPSHOT, _UNSET))
        except Exception as retry_error:
            params['auto_retry_pending'] = False
            params['auto_retry_error'] = str(retry_error)[:300]
            prior = str(run.error or error or '')
            _set(run, train_params=json.dumps(params),
                 phase_detail='Run failed — automatic retry could not start',
                 error=f'{prior} | automatic retry: {retry_error}'[:1000])
            logger.exception('automatic retry for cloud run %s could not start',
                             run.id)
            return None

        params['auto_retry_pending'] = False
        params['auto_retry_run_id'] = result.get('run_id')
        _set(run, train_params=json.dumps(params),
             phase_detail='Run failed — automatic retry launched')
        logger.warning('cloud run %s automatically retried as run %s on %s',
                       run.id, result.get('run_id'), gpu_name)
        return result


def _recover_pending_auto_retries():
    """Complete the persisted claim-to-child crash window at app boot."""
    parents = CloudTrainingRun.query.filter_by(status='error').all()
    for parent in parents:
        if _run_param(parent, 'auto_retry_pending'):
            _maybe_auto_retry(parent, parent.error)


def _prepare_staging(run):
    """Heavy part of the launch, run from the MONITOR thread: staging dirs +
    dataset export (rembg masks — ~1-2 s/image). No-op when staging already
    exists (resume). A failure propagates to the monitor's generic error
    handler (run flips to 'error', slot freed)."""
    if run.staging_dir:
        return
    _set(run, phase_detail='Preparing dataset (masks)…')
    params = json.loads(run.train_params or '{}')
    staging = _staging_root() / f'run_{run.id}'
    (staging / 'samples').mkdir(parents=True, exist_ok=True)
    lt.export_dataset_to_aitoolkit('local', run.dataset_id,
                                   masked=bool(params.get('masked', True)),
                                   dest_dir=str(staging / 'dataset'))
    _set(run, staging_dir=str(staging))


def _register_instance(run, instance_id, offer, token):
    """Isolated so provisioning tests can inject a post-create failure."""
    _set(run, vast_instance_id=str(instance_id), auth_token=token,
         gpu_name=offer.get('gpu_name'), price_per_hour=offer.get('dph_total'),
         status='provisioning', phase_detail='Instance created — booting')


# --- Offer quality layer (2026-07-13, after a dead-cheap 5090 host froze in
# --- 'loading'): the absolute cheapest host of a class is adversely selected
# --- more often than not. Bait prices are excluded, recently-failed hosts are
# --- blacklisted, and at similar price the more RELIABLE host wins. ----------

_PRICE_BAIT_RATIO = 0.60      # offers < 60% of their class median are suspect
_SIMILAR_PRICE_WINDOW = 1.10  # within +10% of cheapest -> reliability decides


def _bad_hosts_path() -> Path:
    return _staging_root() / 'bad_hosts.json'


def _run_machine_id(run):
    """machine_id stamped by _provision into train_params. Defensive like
    _run_family: absent/corrupt params -> None, never an exception (this is
    called from stop/timeout paths that must not fail)."""
    try:
        parsed = json.loads(run.train_params or '{}')
        return parsed.get('machine_id') if isinstance(parsed, dict) else None
    except (ValueError, TypeError):
        return None


def _load_bad_hosts() -> dict:
    """{machine_id(str): {'ts': epoch, 'reason': str}} — expired entries are
    dropped on read (TTL cloud.host_blacklist_days). Corrupt file -> empty."""
    try:
        raw = json.loads(_bad_hosts_path().read_text(encoding='utf-8'))
    except (OSError, ValueError):
        return {}
    if not isinstance(raw, dict):
        return {}
    ttl = float(cfg.get('cloud.host_blacklist_days') or 3) * 86400
    now = _now()
    live = {k: v for k, v in raw.items()
            if isinstance(v, dict) and now - float(v.get('ts') or 0) <= ttl}
    if len(live) != len(raw):
        try:
            _bad_hosts_path().write_text(json.dumps(live), encoding='utf-8')
        except OSError:
            pass
    return live


def _blacklist_host(machine_id, reason):
    """Remember a host whose pod never became ready so the next launch (and the
    tier list) skips it for a few days. Best-effort: never raises."""
    if not machine_id:
        return
    try:
        hosts = _load_bad_hosts()
        hosts[str(machine_id)] = {'ts': _now(), 'reason': str(reason)[:200]}
        _bad_hosts_path().write_text(json.dumps(hosts), encoding='utf-8')
        logger.warning('blacklisted vast host machine_id=%s for %s day(s): %s',
                       machine_id, cfg.get('cloud.host_blacklist_days') or 3, reason)
    except Exception:
        logger.exception('could not blacklist host %s', machine_id)


def _filter_offers(offers) -> list:
    """Drop blacklisted hosts and bait-priced offers (< 60% of their GPU
    class's median price when the class has >= 3 offers — with fewer there is
    no reliable median). Never returns [] when the input wasn't: if every
    offer got filtered, fall back to the input minus blacklisted hosts only
    (renting a suspect host beats failing the run outright)."""
    bad = _load_bad_hosts()
    not_blacklisted = [o for o in offers
                       if str(o.get('machine_id') or '') not in bad]
    by_class = {}
    for o in not_blacklisted:
        by_class.setdefault(o.get('gpu_name') or '', []).append(o)
    kept = []
    for name, group in by_class.items():
        prices = sorted(o['dph_total'] for o in group
                        if o.get('dph_total') is not None)
        if len(prices) >= 3:
            median = prices[len(prices) // 2]
            floor = median * _PRICE_BAIT_RATIO
            group = [o for o in group
                     if o.get('dph_total') is None or o['dph_total'] >= floor]
        kept.extend(group)
    kept.sort(key=lambda o: o.get('dph_total')
              if o.get('dph_total') is not None else 9e9)
    return kept or not_blacklisted


def _best_of(group):
    """Most reliable offer among those within +10% of the group's cheapest —
    a hair more money for a host that actually boots is the right trade."""
    priced = [o for o in group if o.get('dph_total') is not None]
    if not priced:
        return group[0]
    cheapest = min(o['dph_total'] for o in priced)
    window = [o for o in priced if o['dph_total'] <= cheapest * _SIMILAR_PRICE_WINDOW]
    # reliability first; at equal (or absent) reliability the CHEAPEST wins —
    # offers without the field must not silently cost +10%.
    return max(window, key=lambda o: ((o.get('reliability') or 0), -o['dph_total']))


def _pick_offer(offers, requested_gpu, strict=False):
    """Best offer of the requested GPU class if the user picked a speed tier
    and that class is still on the market; otherwise an offer of a
    SIMILAR-OR-BETTER speed tier (≥75% of the requested class's throughput,
    per gpu_speed). 'Best' = most reliable within +10% of the cheapest (see
    _best_of), on offers already stripped of blacklisted hosts and bait
    prices by _filter_offers.

    The historical fallback — cheapest offer of ANY class — handed a $0.13/h
    RTX 3090 to a 12B Krea run when the requested RTX PRO 6000 S sold out
    between the picker and the launch (retry path, user-reported): the
    bottom-barrel is exactly where the flaky hosts live, and the run would
    have been ~3x slower. No similar tier on the market -> actionable error,
    never a silent downgrade."""
    if requested_gpu:
        matches = [o for o in offers if (o.get('gpu_name') or '') == requested_gpu]
        if matches:
            return _best_of(matches)
        if strict:
            raise RuntimeError(
                f'no {requested_gpu} offer is available for the automatic retry')
        floor = gpu_speed.speed_factor(requested_gpu) * 0.75
        similar = [o for o in offers
                   if gpu_speed.speed_factor(o.get('gpu_name')) >= floor]
        if similar:
            return _best_of(similar)
        raise RuntimeError(
            f'no offers similar to {requested_gpu} right now — open the GPU '
            'picker and choose another speed tier')
    return _best_of(offers)


def _disk_gb_for(cloud_cfg, params) -> int:
    """Pod disk size: the configured default, bumped when the run trains on a
    LARGE custom base (stamped remote size). The pod holds the raw download
    plus its quantized working copy plus dataset/checkpoints/HF cache, so the
    bump budgets twice the base size + 30 GB of headroom. Official-base runs
    (no stamp) keep the configured value bit-for-bit."""
    disk_gb = int(cloud_cfg.get('disk_gb') or 60)
    try:
        base_bytes = int(params.get('base_size_bytes') or 0)
    except (TypeError, ValueError):
        base_bytes = 0
    if base_bytes:
        needed = int(base_bytes / 1e9 * 2) + 30
        if needed > disk_gb:
            logger.info('custom base is %.1f GB — pod disk bumped %s -> %s GB',
                        base_bytes / 1e9, disk_gb, needed)
            disk_gb = needed
    return disk_gb


def _provision(run):
    """Search offers and create the instance, honoring the launch-time GPU
    choice when the picked class is still available.
    LEAK-SAFE: any failure after create_instance destroys the instance."""
    c = cfg.get('cloud') or {}
    params = json.loads(run.train_params or '{}')
    fam = params.get('train_type') or 'zimage'
    min_vram = (c.get('min_vram_gb') or {}).get(fam, 24)
    disk_gb = _disk_gb_for(c, params)
    template_hash = (c.get('template_hash') or '').strip()
    # A transient create refusal (offer just taken -> HTTP 400/409, rate limit,
    # vast 5xx — run #80's 'HTTP 400 {}' died here with no retry) gets a bounded
    # re-search: the failed offer is likely gone, so each attempt excludes the
    # offers already tried and picks a fresh one. A non-transient refusal (auth,
    # 404) or an exhausted budget raises immediately.
    tried_offers = set()
    offer = instance_id = None
    token = ''
    for attempt in range(1, _CREATE_INSTANCE_ATTEMPTS + 1):
        offers = vast_client.search_offers(
            min_vram_gb=min_vram, max_dph=c.get('max_price_per_hour', 0.80),
            min_inet_down_mbps=int(c.get('min_inet_down_mbps') or 0),
            min_reliability=float(c.get('min_reliability') or 0.98),
            min_disk_bw_mbps=int(c.get('min_disk_bw_mbps') or 0),
            verified_only=bool(c.get('verified_only', True)),
            secure_cloud_only=bool(c.get('secure_cloud_only', False)))
        pool = [o for o in offers if o.get('offer_id') not in tried_offers]
        if not pool:
            if tried_offers:
                raise RuntimeError(
                    'no fresh vast.ai offer left after a transient create refusal '
                    f'(tried {len(tried_offers)})')
            raise RuntimeError(
                f'no vast.ai offer matches (>= {min_vram} GB VRAM, '
                f'<= ${c.get("max_price_per_hour", 0.80)}/h) — raise the price cap in Settings')
        offer = _pick_offer(_filter_offers(pool), params.get('requested_gpu'),
                            strict=bool(params.get('strict_gpu')))
        tried_offers.add(offer['offer_id'])
        # Stamp the host identity so a boot failure can blacklist THIS machine.
        if offer.get('machine_id') is not None:
            params['machine_id'] = offer['machine_id']
            _set(run, train_params=json.dumps(params))
        try:
            if template_hash:
                # Preferred path (smoke-validated 2026-07-12): the official
                # template publishes the UI behind the pod's Caddy proxy on
                # ui_port and vast generates the per-instance auth token (picked
                # up from the instance record during boot-wait). HF_TOKEN reaches
                # the pod later via ensure_settings(), not env.
                token = ''
                instance_id = vast_client.create_instance(
                    offer['offer_id'], disk_gb=disk_gb,
                    label=run.vast_label, template_hash=template_hash,
                    image=(c.get('image') or None))
            else:
                # Raw-image fallback (config escape hatch): direct port publish +
                # our own bearer token on the UI itself.
                token = pysecrets.token_urlsafe(24)
                port = int(c.get('ui_port') or 18675)
                env = {'AI_TOOLKIT_AUTH': token, f'-p {port}:{port}': '1'}
                hf = cfg.secret('HF_TOKEN')
                if hf:
                    env['HF_TOKEN'] = hf
                instance_id = vast_client.create_instance(
                    offer['offer_id'], disk_gb=disk_gb,
                    label=run.vast_label, image=c.get('image'), env=env,
                    onstart=(c.get('onstart') or None))
            break
        except vast_client.VastError as e:
            if attempt >= _CREATE_INSTANCE_ATTEMPTS or not _is_transient_create_error(e):
                raise
            logger.warning('create_instance attempt %s/%s failed (%s) — retrying '
                           'with a fresh offer', attempt, _CREATE_INSTANCE_ATTEMPTS, e)
            _sleep(_CREATE_INSTANCE_BACKOFF)
    try:
        _register_instance(run, instance_id, offer, token)
    except Exception:
        # the pod exists but we failed to remember it -> kill it NOW, and make
        # the outcome observable (destroy_instance returns False on failure)
        try:
            if not vast_client.destroy_instance(instance_id):
                logger.warning('leak-safe destroy of %s FAILED — instance may still '
                               'be running; boot reconciliation will retry', instance_id)
        except Exception:
            logger.exception('leak-safe destroy of %s raised', instance_id)
        raise


def _idle_seconds(run, now=None) -> float:
    """How long this run has been silent in the DATABASE — the only progress
    signal that survives a restart and does not depend on the monitor thread
    being healthy. Every monitor poll writes phase_detail through _set(), which
    bumps updated_at, so a frozen updated_at means the monitor stopped
    completing iterations (whatever the reason: dead, wedged in a socket read,
    or gone with a restart)."""
    now = now or datetime.utcnow()
    ref = run.updated_at or run.created_at or now
    return max(0.0, (now - ref).total_seconds())


def _monitor_is_responsive(run) -> bool:
    """Can this run's monitor thread be TRUSTED to carry out a stop?

    Both halves matter. A registered thread object proves nothing (the run-103
    monitor was still alive, blocked forever inside one HTTP call), and a fresh
    updated_at alone would be satisfied by a monitor that has just died. Only a
    live thread that is also still writing gets the graceful path."""
    thread = _monitor_threads.get(int(run.id))
    if thread is None or not thread.is_alive():
        return False
    return _idle_seconds(run) <= STOP_HANDOFF_SECONDS


def _force_stop(run, detail, error=None) -> dict:
    """Terminate the pod HERE, without asking the monitor thread.

    The pod is the thing that costs money, and the vast API is the only
    authority on whether it is gone: a successful destroy closes the run as
    'stopped'; a refused or failing destroy must NEVER be reported as a
    success. In that case the run is parked in 'error_pod_kept' — the existing
    status meaning "a pod may still be alive out there" — so boot/launch
    reconciliation reaps it later, and the caller gets the instance id to
    destroy by hand in the meantime."""
    iid = run.vast_instance_id
    _stop_event_for(run.id).set()   # a still-living monitor stands down too
    if not iid:
        _set(run, status='stopped', phase_detail=detail,
             error=error, finished_at=datetime.utcnow())
        return {'ok': True, 'run_id': run.id, 'mode': 'forced',
                'message': detail, 'instance_id': None}
    gone = False
    failure = ''
    try:
        gone = bool(vast_client.destroy_instance(iid))
        if not gone:
            failure = 'the vast.ai API refused the termination'
    except Exception as e:
        failure = str(e)[:200]
        logger.warning('forced stop of run %s: destroy %s failed: %s',
                       run.id, iid, failure)
    if gone:
        _set(run, status='stopped', phase_detail=detail,
             error=error, finished_at=datetime.utcnow())
        logger.warning('forced stop of run %s: pod %s terminated (%s)',
                       run.id, iid, error or detail)
        return {'ok': True, 'run_id': run.id, 'mode': 'forced',
                'message': detail, 'instance_id': iid}
    message = (f'Could not terminate instance {iid} ({failure}). It may still '
               f'be running and billing — destroy it in the vast.ai console.')
    _set(run, status='error_pod_kept', phase_detail=detail[:500],
         error=message, finished_at=datetime.utcnow())
    return {'ok': False, 'run_id': run.id, 'mode': 'failed',
            'error': message, 'instance_id': iid}


def _stop_one(run) -> dict:
    # Decide BEFORE writing anything: stamping stop_requested_at bumps
    # updated_at, which would make a frozen run look freshly alive.
    responsive = _monitor_is_responsive(run)
    _stop_event_for(run.id).set()
    if not run.stop_requested_at:
        _set(run, stop_requested_at=datetime.utcnow())
    if responsive:
        # Graceful: the monitor stops the remote job and rescues the latest
        # checkpoint before terminating. The stamped stop_requested_at arms the
        # supervisor's deadline in case it wedges on the way.
        return {'ok': True, 'run_id': run.id, 'mode': 'graceful',
                'message': 'Stopping the run — the pod is winding down…',
                'instance_id': run.vast_instance_id}
    return _force_stop(
        run,
        detail='Stopped by user — the run monitor was not responding, so the '
               'pod was terminated directly (checkpoints already downloaded '
               'are kept)',
        error='stopped by user without a responsive monitor')


def request_stop(run_id=None) -> dict:
    """Stop one run (or every active run when run_id is None) and report what
    ACTUALLY happened.

    Historically this only set an in-process threading.Event and returned True
    as long as the row was active — so when the monitor thread was dead or
    wedged, the button answered "ok" and the pod kept billing for hours
    (incident 2026-07-25). A stop now either terminates the pod or says it
    could not, naming the instance."""
    if run_id is not None:
        run = CloudTrainingRun.query.get(int(run_id))
        runs = [run] if run and run.status in ACTIVE_STATES else []
    else:
        runs = get_active_runs()
    if not runs:
        return {'ok': False, 'mode': 'none', 'runs': [],
                'error': 'No active cloud run to stop — it may have already '
                         'finished.'}
    results = [_stop_one(run) for run in runs]
    failed = [r for r in results if not r['ok']]
    modes = {r['mode'] for r in results}
    return {'ok': not failed,
            'mode': modes.pop() if len(modes) == 1 else 'mixed',
            'runs': results,
            'message': results[0].get('message', ''),
            'error': failed[0]['error'] if failed else None}


def supervise_active_runs() -> list:
    """One supervisor tick: enforce, from OUTSIDE any monitor thread, the
    guarantees a monitor can no longer make once it is dead or wedged.

    Three rules, all anchored on durable database state:
      * runtime cap  — the configured ceiling used to be a deadline computed
        inside the monitor itself, so the net died with what it protected;
      * stop deadline — a stop handed to a monitor that never carries it out
        (a monitor still streaming the checkpoint down is exempt while it
        keeps writing — see _rescuing_checkpoint);
      * freeze watchdog — no database progress for longer than the phase
        allows (see _freeze_limit_seconds).
    A margin is deliberately left on the first two so a HEALTHY monitor always
    gets to act first: its own paths rescue the last checkpoint from the pod,
    while a forced stop can only keep what mid-run mirroring already pulled.
    Never raises — the whole point is a net that cannot die."""
    acted = []
    try:
        c = cfg.get('cloud') or {}
        max_seconds = int(c.get('max_runtime_minutes') or 480) * 60
        now = datetime.utcnow()
        for run in get_active_runs():
            try:
                age = (now - (run.created_at or now)).total_seconds()
                if age > max_seconds + _SUPERVISOR_MARGIN_SECONDS:
                    res = _force_stop(
                        run, detail='Max runtime reached — pod terminated by '
                                    'the supervisor', error='max runtime cap hit')
                    acted.append({'run_id': run.id, 'reason': 'runtime_cap',
                                  'ok': res['ok']})
                    continue
                stop_age = ((now - run.stop_requested_at).total_seconds()
                            if run.stop_requested_at else 0)
                if stop_age > STOP_DEADLINE_SECONDS \
                        and not _rescuing_checkpoint(run, now):
                    res = _force_stop(
                        run, detail='Stopped by user — the run monitor never '
                                    'completed the stop, so the pod was '
                                    'terminated by the supervisor',
                        error='stop request not honoured in time')
                    acted.append({'run_id': run.id, 'reason': 'stop_deadline',
                                  'ok': res['ok']})
                    continue
                limit = _freeze_limit_seconds(run, c)
                if limit and _idle_seconds(run, now) > limit:
                    res = _force_stop(
                        run, detail=f'Frozen — no progress for {limit // 60} min; '
                                    'pod terminated by the supervisor',
                        error='freeze watchdog')
                    acted.append({'run_id': run.id, 'reason': 'freeze',
                                  'ok': res['ok']})
            except Exception:
                logger.exception('supervisor: run %s could not be judged', run.id)
    except Exception:
        logger.exception('cloud supervisor tick failed')
    return acted


def _rescuing_checkpoint(run, now=None) -> bool:
    """Is this run, right now, pulling its checkpoint off the pod — and still
    writing while it does?

    The stop deadline exists for a monitor that WEDGED after being handed a
    stop. A monitor that is downloading the result is the opposite: it is doing
    the single most valuable part of the stop, and cutting it there throws away
    a checkpoint the user already paid for. The exemption is deliberately
    narrow — it needs the 'downloading' status AND a row written inside the
    handoff window (the transfer heartbeats far more often than that), so a
    monitor that dies mid-transfer stops being spared within a couple of
    minutes and falls back to the freeze watchdog and the runtime cap."""
    return (run.status == 'downloading'
            and _idle_seconds(run, now) <= STOP_HANDOFF_SECONDS)


def _freeze_limit_seconds(run, c=None) -> int:
    """Seconds of database silence tolerated in the run's CURRENT phase (0 =
    watchdog off).

    Only 'training' is judged on the configured value: there the monitor writes
    phase_detail on every poll (~10 s), so silence is unambiguous. Every other
    phase is silent by design for long stretches — staging a big dataset,
    renting and booting a pod, uploading images, pulling the final checkpoint —
    and killing a run that is merely starting up would be worse than the leak
    we are closing. They get a fixed, very generous floor; the runtime cap
    remains their real backstop."""
    c = c if c is not None else (cfg.get('cloud') or {})
    raw = c.get('freeze_watchdog_minutes')
    minutes = _FREEZE_WATCHDOG_MINUTES if raw is None else int(raw or 0)
    if minutes <= 0:
        return 0
    if run.status == 'training':
        return minutes * 60
    return max(minutes * 60, _SILENT_PHASE_FREEZE_SECONDS)


def _supervisor_loop(app):
    while True:
        try:
            with app.app_context():
                supervise_active_runs()
        except Exception:
            logger.exception('cloud supervisor loop failed')
        _sleep(SUPERVISOR_INTERVAL_SECONDS)


def start_supervisor(app):
    """Start the single watchdog thread (idempotent). Deliberately independent
    of boot_recover and of every per-run monitor: it owns nothing, blocks on
    nothing but its own sleep, and therefore survives what they cannot."""
    global _supervisor_thread
    if _supervisor_thread is not None and _supervisor_thread.is_alive():
        return _supervisor_thread
    _supervisor_thread = threading.Thread(
        target=_supervisor_loop, args=(app,), daemon=True, name='cloud-supervisor')
    _supervisor_thread.start()
    return _supervisor_thread


def reconcile_orphans(app) -> int:
    """Boot-time safety net: destroy every 'lds-*' vast instance that no
    active run owns. GENUINELY never raises (boot must not be blocked): the
    whole body — app_context included — sits under a blanket except, so an
    unexpected failure outside the vast_client calls (db not ready, config
    error...) is logged and returns the count destroyed so far.

    error_pod_kept policy: a run in that status deliberately kept its pod
    alive (checkpoint download failed at run completion) so the user can
    recover the checkpoint manually. That pod must NOT be destroyed like a
    plain orphan -- it is spared while `run.finished_at` is within
    cloud.max_runtime_minutes of now, and only reaped past that window (with
    the run annotated, status left untouched -- terminal states stay
    terminal)."""
    destroyed = 0
    try:
        with app.app_context():
            if not cfg.secret('VAST_API_KEY'):
                return 0
            try:
                instances = vast_client.list_instances()
            except Exception as e:
                logger.warning('reconcile: cannot list vast instances: %s', e)
                return 0
            keep = {str(r.vast_instance_id) for r in get_active_runs() if r.vast_instance_id}
            c = cfg.get('cloud') or {}
            max_seconds = int(c.get('max_runtime_minutes') or 480) * 60
            now = datetime.utcnow()
            kept_by_instance = {
                str(r.vast_instance_id): r
                for r in CloudTrainingRun.query.filter_by(status='error_pod_kept').all()
                if r.vast_instance_id}
            for inst in instances:
                label = inst.get('label') or ''
                if not label.startswith('lds-'):
                    continue
                iid = str(inst['instance_id'])
                if iid in keep:
                    continue
                kept_run = kept_by_instance.get(iid)
                if kept_run is not None:
                    # No finished_at (shouldn't happen -- every writer stamps it) means
                    # the recovery window can't be established: fail toward the leak-safety
                    # invariant (reap) rather than sparing an unbounded pod.
                    if kept_run.finished_at and \
                            (now - kept_run.finished_at).total_seconds() <= max_seconds:
                        continue    # still within the manual-recovery window -> spare
                    try:
                        if vast_client.destroy_instance(inst['instance_id']):
                            destroyed += 1
                            logger.warning('reconcile: reaped expired error_pod_kept '
                                           'pod %s (%s)', inst['instance_id'], label)
                            _set(kept_run, error=(kept_run.error or '') +
                                 ' — pod reaped after the recovery window')
                    except Exception as e:
                        logger.warning('reconcile: destroy %s failed: %s',
                                       inst['instance_id'], e)
                    continue
                try:
                    if vast_client.destroy_instance(inst['instance_id']):
                        destroyed += 1
                        logger.warning('reconcile: destroyed orphan pod %s (%s)',
                                       inst['instance_id'], label)
                except Exception as e:
                    logger.warning('reconcile: destroy %s failed: %s',
                                   inst['instance_id'], e)
    except Exception:
        logger.exception('reconcile failed')
    return destroyed


def _start_monitor_for_app(app, run_id):
    """Like _start_monitor but usable outside a request context (boot)."""
    t = threading.Thread(
        target=_monitor, args=(app, run_id), daemon=True, name=f'cloud-train-{run_id}')
    _monitor_threads[int(run_id)] = t
    t.start()


def _start_monitor(run_id):
    from flask import current_app
    _start_monitor_for_app(current_app._get_current_object(), run_id)


def boot_recover(app):
    """Called once at startup (daemon thread). Never raises: a boot recovery
    bug must not prevent the app from serving requests. (1) reconcile any
    'lds-*' pod the DB no longer accounts for; (2) if a run was active when
    the app last closed and its pod was already created, resume monitoring
    it (the pod kept training/uploading in our absence); (3) if it never got
    a pod (crashed during 'preparing'), there is nothing to resume -> flip
    it to 'error' so its slot is freed. Iterates every active run (not just
    one) so a restart with several concurrent runs resumes all of them."""
    try:
        reconcile_orphans(app)
        with app.app_context():
            if not cfg.secret('VAST_API_KEY'):
                return
            for run in get_active_runs():
                if run.vast_instance_id:
                    logger.info('resuming cloud run %s (pod %s kept training)',
                                run.id, run.vast_instance_id)
                    _start_monitor_for_app(app, run.id)
                else:
                    _set(run, status='error', finished_at=datetime.utcnow(),
                         error='app restarted before the pod was created')
            _recover_pending_auto_retries()
    except Exception:
        logger.exception('cloud boot recovery failed')


POLL_SECONDS = 10
_CKPT_SYNC_EVERY_POLLS = 12          # mid-run checkpoint mirror every ~2 min
READY_TIMEOUT_SECONDS = 900          # 15 min: boot + image pull
UNREACHABLE_GRACE_SECONDS = 360      # default tolerated mid-run network blackout
                                     # (overridable: cloud.unreachable_grace_minutes)
_CREATE_INSTANCE_ATTEMPTS = 3        # bounded retry on a transient vast create refusal
_CREATE_INSTANCE_BACKOFF = 5         # seconds between create attempts
_sleep = time.sleep


def _now():
    return time.time()


def _make_remote(run) -> RemoteAiToolkit:
    return RemoteAiToolkit(run.base_url, run.auth_token)


def _cloudify_job_config(job_config: dict, job_name: str,
                         staging_dataset: str, pod_settings: dict,
                         run_params: dict | None = None) -> dict:
    """Rewrite the locally-built config for the pod: remote paths, remote
    trainer type (DB status updates), and the job name the pod's routes key
    on. The staging->pod path swap is done on the JSON text so every field
    referencing the staging dir (folder_path, mask_path) is rewritten at
    once, backslash-escaping included.

    Custom base (run_params carries base_repo_id): the symmetric seam to the
    dataset swap — build_job_config emitted the LOCAL custom path (single file
    or converted diffusers dir), which means nothing on the pod; route
    model.name_or_path to the PRIVATE HF repo the base was pushed to, and the
    pod downloads it with the user's HF_TOKEN exactly like the gated official
    bases. Krea additionally pins model_kwargs.checkpoint_filename (its loader
    fetches ONE file from the repo); Klein derives its hardcoded per-size
    filename from the arch; Z-Image loads the repo's transformer/ subfolder."""
    pod_ds = pod_settings['DATASETS_FOLDER'].rstrip('/') + '/' + job_name
    text = json.dumps(job_config)
    needle = json.dumps(str(staging_dataset))[1:-1]     # JSON-escaped form
    text = text.replace(needle, pod_ds)
    out = json.loads(text)
    conf = out['config']
    conf['name'] = job_name
    proc = conf['process'][0]
    # The local build emits the legacy 'sd_trainer' uid; the pod's ai-toolkit
    # runs the modern 'diffusion_trainer' path (the universal ui/api trainer
    # whose progress events the pod UI's DB understands), so retype it here. A
    # slider run already emits 'concept_slider' — a first-class built-in
    # extension that itself extends DiffusionTrainer — which the pod runs as-is;
    # flattening it to diffusion_trainer would silently drop the slider loss and
    # train an ordinary LoRA. Only the standard trainer is retyped.
    if proc.get('type') == 'sd_trainer':
        proc['type'] = 'diffusion_trainer'
    proc['training_folder'] = pod_settings['TRAINING_FOLDER']
    proc['device'] = 'cuda:0'
    # Dual captions are LOCAL-ONLY for now: remote.upload_dataset only ships the images
    # and their .txt sidecars (its extension filter skips the JSON caption file), so a
    # pod folder_path pointing at that missing JSON would find zero images. Revert to the
    # historical folder + .txt sidecars — the run trains with long captions only. The
    # earlier blanket path-swap already mangled the JSON folder_path; overwrite it cleanly.
    train = proc.get('train') or {}
    if train.pop('short_and_long_captions', None):
        datasets = proc.get('datasets') or []
        if datasets:
            datasets[0]['folder_path'] = pod_ds
            datasets[0].setdefault('caption_ext', 'txt')
    base_repo = (run_params or {}).get('base_repo_id')
    if base_repo:
        from . import hf_base_push
        fam = (run_params or {}).get('train_type')
        model = proc.get('model') or {}
        model['name_or_path'] = base_repo
        fname = hf_base_push.weight_filename(
            fam, (run_params or {}).get('variant'), base_repo.split('/')[-1])
        if fam == 'krea' and fname:
            kwargs = dict(model.get('model_kwargs') or {})
            kwargs['checkpoint_filename'] = fname
            model['model_kwargs'] = kwargs
        proc['model'] = model
    return out


def _finish(run, status, detail='', error=None, destroy=True):
    # A paid retry must never overlap the failed pod. Return whether there is
    # confirmed to be no old pod left; callers that do not retry ignore it.
    pod_gone = not bool(run.vast_instance_id)
    if destroy and run.vast_instance_id:
        try:
            pod_gone = bool(vast_client.destroy_instance(run.vast_instance_id))
            if not pod_gone:
                logger.error('terminate %s returned false', run.vast_instance_id)
        except Exception as e:
            pod_gone = False
            logger.warning('terminate %s failed: %s', run.vast_instance_id, e)
    _set(run, status=status, phase_detail=detail, error=error,
         finished_at=datetime.utcnow())
    return pod_gone


class _RunClosedExternally(Exception):
    """The run row left ACTIVE_STATES while this monitor was working — a forced
    stop or the supervisor closed it. The monitor must stand down instead of
    resurrecting the row (or renting a pod for a run nobody waits for)."""


def _assert_run_open(run):
    db.session.refresh(run)     # another thread may have committed a close
    if run.status not in ACTIVE_STATES:
        raise _RunClosedExternally(run.status)


def _finish_if_open(run, status, detail='', error=None, destroy=True):
    """_finish(), but only for a run that is still ours to close.

    Checking ONCE at the top of the poll loop is not enough. Every terminal
    branch does minutes of work after that check — stopping the remote job,
    pulling the final checkpoint, importing it, mirroring it locally — and the
    supervisor is a different thread on a different session: it can force-stop
    the run, destroy the pod and write the row inside that window. The monitor
    would then rewrite a closed row and announce a pod it 'kept' that no longer
    exists. Re-asserting immediately before the write means a run closed behind
    our back raises _RunClosedExternally and takes the stand-down path instead
    (the work done up to here — the downloaded checkpoint — is kept on disk)."""
    _assert_run_open(run)
    return _finish(run, status, detail=detail, error=error, destroy=destroy)


def _monitor(app, run_id):
    """Full run lifecycle. Runs in a daemon thread; every exit path goes
    through _finish() so the pod cannot be leaked by this thread."""
    with app.app_context():
        run = CloudTrainingRun.query.get(run_id)
        if not run:
            _stop_events.pop(int(run_id), None)
            _monitor_threads.pop(int(run_id), None)
            return
        stop_event = _stop_event_for(run_id)
        c = cfg.get('cloud') or {}
        max_seconds = int(c.get('max_runtime_minutes') or 480) * 60
        # The runtime cap must survive restarts: anchor it to the run's durable
        # created_at (backdate the local clock by the run's age), not to this
        # thread's start.
        run_age = max(0.0, (datetime.utcnow() - (run.created_at or datetime.utcnow())).total_seconds())
        cap_anchor = _now() - run_age
        # Whether we ENTER the monitor already owning a pod (app restarted while
        # it was still booting) — captured BEFORE _provision, which sets
        # vast_instance_id on a fresh launch. It decides the boot-readiness
        # anchor below.
        resuming_existing_pod = bool(run.vast_instance_id)
        try:
            # -- heavy launch work, moved off the HTTP path (see launch) ----
            _prepare_staging(run)
            _assert_run_open(run)       # never rent for an already-stopped run
            # -- provision (if resuming, the instance may already exist) ----
            if not run.vast_instance_id:
                _provision(run)
            _assert_run_open(run)
            # Boot-readiness timeout anchor. A FRESH launch measures from now
            # (post-provision) so dataset staging / offer search never eat into
            # the pod's boot budget. A RESUME must NOT get a brand-new window on
            # every restart: that let a pod whose UI never answered survive
            # 37 min across two restarts instead of the 15-min READY_TIMEOUT
            # (incident 2026-07-14). On resume we anchor to the DURABLE
            # created_at (cap_anchor), so readiness measures the TOTAL time since
            # launch across every restart — the intended behaviour even for a pod
            # that was honestly still booting.
            boot_started = cap_anchor if resuming_existing_pod else _now()

            # -- wait until the pod's UI answers ----------------------------
            # Readiness is checked BEFORE the elapsed-time read: an
            # already-booted pod (the common case, and every resumed run)
            # must be able to break out on the very first iteration without
            # ever touching _now() -- a test clock that jumps in large
            # strides per call must not misfire this boot-timeout on a pod
            # that was, in fact, instantly ready.
            template_mode = bool((c.get('template_hash') or '').strip())
            ready_timeout = (int(c.get('ready_timeout_minutes') or 0) * 60
                             or READY_TIMEOUT_SECONDS)
            _set(run, phase_detail='Waiting for the pod to boot')
            port = int(c.get('ui_port') or 18675)
            if template_mode and port == 8675:
                # 8675 is the pre-template default that Settings saves may have
                # baked into config.json; the official template only publishes
                # the UI behind the pod proxy on 18675 — a stale 8675 makes the
                # boot-wait spin for its whole budget (observed live 2026-07-12).
                logger.warning('cloud.ui_port=8675 is stale for template mode — using 18675')
                port = 18675
            while True:
                _assert_run_open(run)
                # A transient vast API hiccup is just "not ready yet" -- only
                # READY_TIMEOUT_SECONDS may fail the boot wait, never a single
                # 502 that would destroy a pod about to come up fine.
                try:
                    inst = vast_client.get_instance(run.vast_instance_id)
                except vast_client.VastError as e:
                    logger.warning('boot-wait: vast API hiccup (%s) — retrying', e)
                    inst = None
                # Template launches authenticate with the vast-generated
                # per-instance token (the pod's Caddy proxy accepts it as a
                # Bearer header) — pick it up as soon as the record shows it.
                if inst and not run.auth_token and inst.get('jupyter_token'):
                    _set(run, auth_token=inst['jupyter_token'])
                base = vast_client.derive_base_url(inst, port) if inst else None
                ready = False
                if base:
                    if run.base_url != base:
                        _set(run, base_url=base)
                    ready = _make_remote(run).is_ready()
                    if ready:
                        break
                # Honor "Stop run" DURING boot too — but only on a pod that is
                # NOT ready yet (a ready pod breaks out above and the training
                # loop handles the stop normally). Without this, the boot-wait
                # spun its whole 25-min budget on a dead host while the stop
                # button silently did nothing (observed live 2026-07-13, a
                # 5090 stuck in 'loading'). No job exists yet -> terminate.
                if stop_event.is_set():
                    stop_event.clear()
                    # A user killing a boot this late is almost always a stuck
                    # host — blacklist it like a timeout would. An early stop
                    # (changed their mind) says nothing about the host.
                    if _now() - boot_started > 8 * 60:
                        _blacklist_host(_run_machine_id(run),
                                        'user stopped a boot stuck past 8 min')
                    _finish(run, 'stopped', detail='Stopped by user during boot')
                    return
                # Live telemetry: surface WHERE the boot is stuck (image pull,
                # port publication, UI warm-up) in the UI phase line and the
                # log — runs #3/#4 died blind on 'Waiting for the pod to boot'.
                st = (inst or {}).get('actual_status') or 'not listed yet'
                has_ports = bool(((inst or {}).get('ports') or {}).get(f'{port}/tcp'))
                stage = (f'pod {st}' if not has_ports
                         else 'pod up — waiting for the UI to answer')
                detail = f'Waiting for the pod to boot — {stage}'
                if run.phase_detail != detail:
                    logger.info('boot-wait run %s: status=%s port_%s_published=%s '
                                'base=%s ready=%s', run.id, st, port, has_ports,
                                base or '-', ready)
                    _set(run, phase_detail=detail)
                if _now() - boot_started > ready_timeout:
                    # This host burned the whole boot budget — skip it for the
                    # next few days so a relaunch can't land on it again.
                    _blacklist_host(_run_machine_id(run),
                                    'pod did not become ready in time')
                    raise RuntimeError('pod did not become ready in time')
                _sleep(POLL_SECONDS)

            remote = _make_remote(run)

            # -- resume contract: an already-submitted job (app restarted
            # mid-run) skips settings/upload/create/start entirely and goes
            # straight to polling the existing remote job. ------------------
            if not run.remote_job_id:
                pod_settings = remote.ensure_settings(hf_token=cfg.secret('HF_TOKEN'))

                # -- upload dataset (+ masks folder if present) --------------
                _set(run, status='uploading', phase_detail='Uploading dataset')
                staging_dataset = os.path.join(run.staging_dir, 'dataset')
                remote.upload_dataset(run.job_name, staging_dataset)
                masks_dir = staging_dataset + '_masks'
                if os.path.isdir(masks_dir) and os.listdir(masks_dir):
                    remote.upload_dataset(run.job_name + '_masks', masks_dir)

                # -- build + submit the job -----------------------------------
                # Build from the run's STAMPED family/variant, NEVER the dataset's
                # current train_type/train_variant: a later launch on the same
                # dataset (or a /train-type change) may have moved that row since
                # this run launched, and this rebuild happens minutes later at pod
                # boot. _run_config_dataset presents the run's own launch params
                # so two concurrent multi-family runs each get their own arch
                # (incident 2026-07-14 — see _RunConfigDataset).
                params = json.loads(run.train_params or '{}')
                ds = fds.get_dataset('local', run.dataset_id)
                job_config = lt.build_job_config(
                    _run_config_dataset(ds, params),
                    staging_dataset, steps=params.get('steps') or 3000,
                    training_folder='__POD__')
                job_config = _cloudify_job_config(job_config, run.job_name,
                                                  staging_dataset, pod_settings,
                                                  run_params=params)
                job_id, adopted = _create_or_adopt_job(run, remote, job_config)
                # Persist the id THE INSTANT the job exists on the pod, before
                # the (slow) seeding and the start. Recording it only after
                # start_job left a window in which the pod already held the job
                # but our row still said remote_job_id=NULL — an app restart
                # inside that window sent the resume straight back into this
                # branch, where the pod refused the duplicate name with
                # 409 "Job name already exists" and the run died with the money
                # already spent (run #107, ~1 h of 5090 time). The run is NOT
                # yet 'training' here: only start_job earns that status, and the
                # resume branch relies on the distinction.
                _set(run, remote_job_id=job_id,
                     phase_detail='Job created on the pod')
                if adopted:
                    # The pod already had this job (this run's earlier attempt).
                    # Never blind-start it: it may be mid-training.
                    _ensure_remote_job_started(run, remote, job_id, pod_settings)
                else:
                    # Continue-in-cloud: drop the source checkpoint into the
                    # job's save_root BEFORE start so ai-toolkit auto-resumes.
                    _seed_resume_checkpoint(run, remote, pod_settings)
                    remote.start_job(job_id)
                    _set(run, status='training',
                         phase_detail='Job queued on the pod')
            else:
                job_id = run.remote_job_id
                _set(run, phase_detail='Resuming — reattaching to running job')
                _ensure_remote_job_started(run, remote, job_id)

            # -- poll until terminal ------------------------------------------
            # Two watchdogs share one progress clock (last_progress_ts):
            #  * stall — once training has produced a step, kill if the step
            #    counter freezes past stall_timeout_minutes.
            #  * first-step — BEFORE the first step (base download, quantize,
            #    latent caching) kill if step 1 is never reached in time. Only
            #    the runtime cap used to bound this phase, so a pod whose base
            #    download collapsed to a crawl burned the WHOLE cap for zero
            #    steps (run #75: 26.3 GB base at ~12 kB/s, 10h45 / 7 € / 0 saves
            #    — 2026-07-19). A healthy Krea-2-Raw run reaches step 1 in a few
            #    minutes (its full 2000-step run was ~84 min), so the default is
            #    generous enough to survive an honestly slow download.
            stall_seconds = int(c.get('stall_timeout_minutes') or 30) * 60
            first_step_seconds = int(c.get('first_step_timeout_minutes') or 45) * 60
            grace_seconds = (int(c.get('unreachable_grace_minutes') or 0) * 60
                             or UNREACHABLE_GRACE_SECONDS)
            last_step = -1
            last_progress_ts = _now()
            # Time of the FIRST failure of the current unreachable streak (None
            # while the pod answers). The grace must measure CONSECUTIVE get_job
            # failure time, not time-since-last-success: the per-poll log/sample
            # mirror and checkpoint sync can each block for tens of seconds on a
            # degrading vast proxy, and anchoring to the last success would let
            # that non-probe time silently eat the grace and declare a still-live
            # pod 'unreachable' on its very first failed probe.
            unreachable_since = None
            polls = 0
            while True:
                _assert_run_open(run)
                if _now() - cap_anchor > max_seconds:
                    try:
                        remote.stop_job(job_id)
                    except Exception:
                        pass
                    _try_download_checkpoint(run, remote, allow_stale=True)
                    _finish_if_open(run, 'stopped',
                                    detail='Max runtime reached — pod terminated',
                                    error='max runtime cap hit')
                    return
                if stop_event.is_set():
                    stop_event.clear()
                    _set(run, phase_detail='Stopping on user request')
                    try:
                        remote.stop_job(job_id)
                    except Exception:
                        pass
                    _try_download_checkpoint(run, remote, allow_stale=True)
                    _finish_if_open(run, 'stopped', detail='Stopped by user')
                    return
                try:
                    job = remote.get_job(job_id)
                    unreachable_since = None
                except Exception as e:
                    now = _now()
                    if unreachable_since is None:
                        unreachable_since = now
                    if now - unreachable_since > grace_seconds:
                        raise RuntimeError(f'pod unreachable: {e}')
                    _sleep(POLL_SECONDS)
                    continue

                _pull_log_and_samples(run, remote, job_id)
                # Mid-run checkpoint mirror, throttled (~2 min at 10 s polls):
                # list_files is cheap, but no need to hammer it every poll —
                # the pod only writes a new save every save_every steps.
                polls += 1
                if polls % _CKPT_SYNC_EVERY_POLLS == 0:
                    _sync_latest_checkpoint(run, remote)
                status = job.get('status')
                info = job.get('info') or ''
                _set(run, phase_detail=f"{status}: {info}"[:500])

                if status == 'completed':
                    ok = _try_download_checkpoint(run, remote)
                    if not ok:
                        # A host that cannot DELIVER its result (even through
                        # the resume loop) is a bad host — skip it next time.
                        _blacklist_host(_run_machine_id(run),
                                        'could not serve the final checkpoint')
                        # LoRA > a few minutes of pod time: keep the pod for
                        # manual recovery; max-runtime/reconcile will reap it.
                        # Same guard as _finish_if_open: announcing a kept pod
                        # for a run the supervisor just force-stopped would
                        # point the user at an instance that is already gone.
                        _assert_run_open(run)
                        _set(run, status='error_pod_kept',
                             error='checkpoint download failed — pod kept, '
                                   f'recover manually at {run.base_url}',
                             finished_at=datetime.utcnow())
                        return
                    _download_intermediates(run, remote)
                    _import_result(run)
                    _mirror_into_local_run(run)
                    _finish_if_open(run, 'done', detail='Training complete')
                    return
                if status in ('error', 'stopped'):
                    _try_download_checkpoint(run, remote, allow_stale=True)
                    _finish_if_open(run, 'error' if status == 'error' else 'stopped',
                                    detail=f'Remote job {status}', error=info or status)
                    return
                # -- stall watchdog: guiding rule — NEVER kill a run that
                # progresses. The elif keeps a progressing poll from ever
                # evaluating the stall clock (a coarse test clock jumping in
                # large strides per call must not misfire on a healthy run).
                step = job.get('step') or 0
                if step > last_step:
                    last_step = step
                    last_progress_ts = _now()
                elif last_step > 0 and (_now() - last_progress_ts) > stall_seconds:
                    try:
                        remote.stop_job(job_id)
                    except Exception:
                        pass
                    _try_download_checkpoint(run, remote, allow_stale=True)
                    _finish_if_open(run, 'error',
                                    detail='Stalled — no step progress for '
                                           f'{stall_seconds // 60} min; pod terminated',
                                    error='stall watchdog')
                    return
                elif last_step <= 0 and (_now() - last_progress_ts) > first_step_seconds:
                    # No training step in first_step_timeout_minutes — the pod is
                    # wedged before step 1 (typically the base-model download
                    # crawling; nothing to rescue since no checkpoint exists).
                    try:
                        remote.stop_job(job_id)
                    except Exception:
                        pass
                    _finish_if_open(run, 'error',
                                    detail='No training step reached in '
                                           f'{first_step_seconds // 60} min — pod likely '
                                           'stuck downloading the base model; terminated',
                                    error='first-step watchdog')
                    return
                _sleep(POLL_SECONDS)
        except _RunClosedExternally as closed:
            # Someone with more authority than this thread (a forced stop, the
            # supervisor) already closed the run. Do NOT touch the row -- but a
            # pod we may have just rented is still ours to kill, unless the row
            # says it was deliberately kept for manual recovery.
            logger.warning('cloud run %s closed externally (%s) — monitor '
                           'standing down', run_id, closed)
            if run.vast_instance_id and run.status != 'error_pod_kept':
                try:
                    vast_client.destroy_instance(run.vast_instance_id)
                except Exception:
                    logger.exception('stand-down destroy of %s raised',
                                     run.vast_instance_id)
        except Exception as e:
            logger.exception('cloud run %s failed', run_id)
            error_text = str(e)[:500]
            retryable = _is_retryable_pod_failure(error_text)
            # Exclude the failed host before selecting the fresh pod.
            if retryable:
                _blacklist_host(_run_machine_id(run),
                                f'transient pod failure: {error_text[:160]}')
            pod_gone = _finish(run, 'error', detail='Run failed',
                               error=error_text)
            if retryable and pod_gone:
                _maybe_auto_retry(run, error_text)
            elif retryable:
                _set(run, phase_detail='Run failed — automatic retry withheld '
                                       'because pod termination was not confirmed')
        finally:
            # This run's slot in the module maps is done with — drop it so
            # they cannot grow unbounded across the app's lifetime with many
            # concurrent runs coming and going.
            _stop_events.pop(int(run_id), None)
            _monitor_threads.pop(int(run_id), None)
            _sync_state.pop(int(run_id), None)


# A run that has reached one of these has provably had its remote job STARTED
# (only the post-start_job write sets 'training'). Anything earlier means the
# job may exist on the pod without ever having been launched.
_JOB_STARTED_STATES = ('training', 'downloading', 'terminating')


def _create_or_adopt_job(run, remote, job_config):
    """Submit this run's job, or ADOPT the one already on the pod.

    Returns (job_id, adopted). The pod's job `name` is unique, and ours is
    `lds<run.id>_<run_name>` — stable for the life of the run and derived from a
    primary key, so a 409 on submit can only mean THIS run already created THIS
    job on THIS pod (an earlier attempt whose id never reached our row). Killing
    the run over a duplicate of its own job wastes an already-paid hour, so the
    id is read back from the pod's job list and the run continues.

    If the list cannot resolve the name, the run still fails — but with an error
    that says what happens next and what becomes of the pod."""
    try:
        return remote.create_job(run.job_name, job_config), False
    except Exception as e:
        if 'HTTP 409' not in str(e):
            raise
        logger.warning('run %s: the pod already holds job %r (409) — adopting it '
                       'instead of failing the run', run.id, run.job_name)
        existing = None
        try:
            existing = remote.find_job_by_name(run.job_name)
        except Exception:
            logger.exception('run %s: could not list the pod jobs to adopt %r',
                             run.id, run.job_name)
        job_id = str((existing or {}).get('id') or '')
        if job_id:
            _set(run, phase_detail='Reattached to the job already on the pod')
            return job_id, True
        raise RuntimeError(
            f'this pod already holds a training job named "{run.job_name}" '
            'but would not say which one, so it cannot be reattached. The pod '
            'is being terminated so it stops costing money; any checkpoint it '
            'had already produced is lost. Use "Retry" on this run to relaunch '
            'on a fresh pod — a retry gets a new job name, so it cannot hit '
            'this again.')


def _ensure_remote_job_started(run, remote, job_id, pod_settings=None):
    """Guarantee the remote job is actually RUNNING, not merely created.

    ai-toolkit creates a job with status 'stopped' and only `start` moves it to
    'queued'. The poll loop below reads 'stopped' as a terminal state, so a job
    that exists but was never started would kill the run at the first poll —
    exactly the bug traded in if the id were recorded early and nothing else
    changed. A run past `_JOB_STARTED_STATES` provably started its job; anything
    earlier asks the pod, and starts (after re-seeding any resume checkpoint,
    which must land before the first step) only a job still sitting at
    'stopped' with no step. Never blind-starts: re-queuing a live job would
    disturb a run that is training fine."""
    if run.status in _JOB_STARTED_STATES:
        return
    try:
        job = remote.get_job(job_id) or {}
    except Exception as e:
        # Not fatal here: the poll loop owns pod reachability and its grace
        # window. Guessing 'never started' on an unreachable pod could re-queue
        # a job that is training.
        logger.warning('run %s: could not read job %s to check whether it was '
                       'started (%s) — leaving it to the poll loop', run.id, job_id, e)
        return
    if (job.get('status') or 'stopped') != 'stopped' or (job.get('step') or 0) > 0:
        _set(run, status='training')     # already live (or finished) — poll it
        return
    logger.warning('run %s: job %s exists on the pod but was never started — '
                   'starting it now', run.id, job_id)
    _set(run, phase_detail='Resuming — the job was created but never started')
    _seed_resume_checkpoint(run, remote,
                            pod_settings if pod_settings is not None
                            else remote.get_settings())
    remote.start_job(job_id)
    _set(run, status='training', phase_detail='Job queued on the pod')


def _seed_resume_checkpoint(run, remote, pod_settings):
    """Continue-in-cloud: place the source run's harvested checkpoint into THIS
    job's save_root on the pod so ai-toolkit's auto-resume finds it — it globs
    <TRAINING_FOLDER>/<job_name>/<job_name>*.safetensors, takes the newest by
    ctime, and reads the resume step from the safetensors metadata. The file is
    renamed to THIS job's prefix so the glob matches (the save the trainer would
    itself write). No resume checkpoint stamped in train_params -> no-op (a
    normal launch). A missing/failed seed RAISES: a 'continue' that cannot
    resume must fail loudly, never silently train from scratch."""
    src = _run_param(run, 'resume_ckpt_path')
    if not src:
        return
    if not os.path.isfile(src):
        raise RuntimeError(f'resume checkpoint vanished before upload: {src}')
    step = int(_run_param(run, 'resume_step') or 0)
    remote_name = f'{run.job_name}_{step:09d}.safetensors'
    training_folder = pod_settings['TRAINING_FOLDER'].rstrip('/')
    dest_dir = f'{training_folder}/{run.job_name}'
    _set(run, phase_detail='Seeding checkpoint for resume…')
    remote.seed_checkpoint(pod_settings['DATASETS_FOLDER'], dest_dir,
                           remote_name, src)
    logger.info('run %s: seeded resume checkpoint %s -> %s',
                run.id, os.path.basename(src), dest_dir)


def _pull_log_and_samples(run, remote, job_id):
    """Mirror remote log + new samples into staging so cloud_progress reuses
    the exact local parsing/serving machinery. Never raises."""
    try:
        text = remote.get_log(job_id)
        with open(os.path.join(run.staging_dir, 'training.log'), 'w',
                  encoding='utf-8', errors='replace') as fh:
            fh.write(text)
    except Exception as e:
        logger.debug('log mirror failed: %s', e)
    try:
        samples_dir = os.path.join(run.staging_dir, 'samples')
        have = set(os.listdir(samples_dir))
        for remote_path in remote.get_samples(job_id):
            name = os.path.basename(remote_path.replace('\\', '/'))
            if name and name not in have:
                remote.download_sample(remote_path,
                                       os.path.join(samples_dir, name))
    except Exception as e:
        logger.debug('sample mirror failed: %s', e)


def _newest_remote_checkpoint(remote, job_id):
    """The newest .safetensors file entry ({'path', 'size'}), or None.
    ai-toolkit zero-pads step numbers, so lexicographic order IS step order."""
    files = [f for f in remote.list_files(job_id)
             if f.get('path', '').endswith('.safetensors')]
    if not files:
        return None
    return sorted(files, key=lambda f: f['path'])[-1]


def _fetch_checkpoint(run, remote, ckpt, timeout=None, attempts=3,
                      on_progress=None) -> str:
    """Download the checkpoint entry ({'path','size'}) into staging and return
    the local path. Skips the transfer when this exact save is already local
    (the mid-run sync usually got there first). Two integrity layers:
    - a KILLED transfer never lands at dest (RemoteAiToolkit._download's own
      .part-then-rename; no second layer here — it produced '.part.part');
    - a TRUNCATED transfer that ends with a clean EOF (observed live
      2026-07-13: pods closing the stream after a few chunks while training)
      is caught by comparing the byte size against list_files' size — a short
      file is deleted and the fetch fails rather than registering garbage."""
    remote_path = ckpt['path']
    name = os.path.basename(remote_path.replace('\\', '/'))
    dest = os.path.join(run.staging_dir, name)
    if run.checkpoint_local_path and os.path.isfile(dest) \
            and os.path.basename(run.checkpoint_local_path) == name:
        return dest
    remote.download_public_file(remote_path, dest, timeout=timeout,
                                expected_size=ckpt.get('size'), attempts=attempts,
                                on_progress=on_progress)
    want = int(ckpt.get('size') or 0)
    got = os.path.getsize(dest)
    if want and got != want:
        try:
            os.remove(dest)
        except OSError:
            pass
        raise RuntimeError(f'truncated download of {name}: {got}/{want} bytes')
    return dest


_SYNC_DL_TIMEOUT = 60      # opportunistic pull: fail fast, the loop must not hang
_SYNC_MAX_FAILS = 3        # give up on a save after this; a NEWER save retries
_sync_state = {}           # run_id -> {'name': save filename, 'fails': int}


def _sync_latest_checkpoint(run, remote):
    """Mid-run mirror of the pod's newest SAVE: if the host dies at step 3000
    the local copy of the step-2750 save survives, instead of everything being
    lost because downloads only happened at run end (user-observed gap,
    2026-07-13). Never raises, never flips the run's status. EVERY synced save
    is KEPT (user ask: harvest ALL trained epochs) — the pod prunes its own
    saves to max_step_saves, so grabbing each one as it appears is the only
    way to collect the full epoch history; disk is reclaimed via the 🗑/🧹
    tools and the trash.

    Some pods cannot serve big files WHILE training (observed live: streams
    die after a few chunks) — after _SYNC_MAX_FAILS failed attempts on the
    same save we stop retrying it (a newer save resets the counter), and each
    attempt is capped at _SYNC_DL_TIMEOUT so a trickling stream cannot hold
    the monitor loop — and with it the stop button — for minutes."""
    try:
        ckpt = _newest_remote_checkpoint(remote, run.remote_job_id)
        if not ckpt:
            return
        name = os.path.basename(ckpt['path'].replace('\\', '/'))
        st = _sync_state.get(run.id)
        if st and st.get('name') == name and st.get('fails', 0) >= _SYNC_MAX_FAILS:
            return
        prev = run.checkpoint_local_path
        try:
            dest = _fetch_checkpoint(run, remote, ckpt,
                                     timeout=_SYNC_DL_TIMEOUT)
        except Exception as e:
            st = _sync_state.setdefault(run.id, {'name': name, 'fails': 0})
            if st.get('name') != name:
                st.update(name=name, fails=0)
            st['fails'] += 1
            # First failure at WARNING so it is visible in the log viewer;
            # repeats at DEBUG (the give-up cap bounds them anyway).
            log = logger.warning if st['fails'] == 1 else logger.debug
            log('mid-run checkpoint sync of %s failed (attempt %s/%s): %s',
                name, st['fails'], _SYNC_MAX_FAILS, e)
            return
        _sync_state.pop(run.id, None)
        if dest != prev:
            # checkpoint_local_path tracks the NEWEST save; earlier synced
            # saves stay on disk (full epoch harvest).
            _set(run, checkpoint_local_path=dest)
    except Exception as e:
        logger.debug('mid-run checkpoint sync failed: %s', e)


_DOWNLOAD_HEARTBEAT_SECONDS = 20


def _transfer_size(got, want) -> str:
    got_mb = (got or 0) / 1e6
    return f'{got_mb:.0f} / {want / 1e6:.0f} MB' if want else f'{got_mb:.0f} MB'


def _download_heartbeat(run, name):
    """Progress callback for a long checkpoint transfer.

    A transfer of tens of minutes must not LOOK like a dead monitor. Every
    safety net in this module reads database progress and nothing else, so a
    silent transfer is indistinguishable from a wedged thread — and the pod
    would be terminated exactly while we are rescuing the thing the run was
    for. Beating updated_at from inside the stream is what makes the two
    distinguishable; the user gets a moving figure out of it too.

    Throttled, and it never raises: a heartbeat that cannot write must not
    sink a transfer that is otherwise working."""
    state = {'ts': 0.0}

    def beat(got, want):
        now = _now()
        if now - state['ts'] < _DOWNLOAD_HEARTBEAT_SECONDS:
            return
        state['ts'] = now
        try:
            _set(run, phase_detail=f'Downloading {name} — '
                                   f'{_transfer_size(got, want)}'[:500])
        except Exception:
            logger.debug('download heartbeat could not write', exc_info=True)

    return beat


def _try_download_checkpoint(run, remote, allow_stale=False) -> bool:
    """Download the newest .safetensors into staging. False on failure.
    allow_stale (rescue paths — stop/stall/cap): when the pod can't serve the
    newest save anymore, an already-synced OLDER save still counts as success.
    The COMPLETION path must stay strict (allow_stale=False): falling back to
    an older save there would silently discard the final training steps —
    error_pod_kept keeps the pod so the user can recover the real result."""
    try:
        ckpt = _newest_remote_checkpoint(remote, run.remote_job_id)
        if ckpt:
            name = os.path.basename(ckpt['path'].replace('\\', '/'))
            # The status flips BEFORE the transfer, not after it. This is the
            # end of a run that WORKED, and the transfer can take tens of
            # minutes on a pod proxy that cuts the stream every couple of MB.
            # While it was still labelled 'training' the freeze watchdog judged
            # it on the training threshold (45 min of database silence) with a
            # frozen updated_at — it would have destroyed the pod mid-rescue,
            # throwing away a checkpoint already paid for. 'downloading' is an
            # ACTIVE state judged on the silent-phase floor, and the heartbeat
            # below keeps even that from being needed.
            _set(run, status='downloading',
                 phase_detail=f'Downloading {name}…'[:500])
            # Large attempts budget: a sick-proxy host cutting the stream
            # every ~0.5-2 MB still delivers an 85 MB file via ~100 resumed
            # connections (validated live 2026-07-13, run #7's manual rescue).
            dest = _fetch_checkpoint(run, remote, ckpt, attempts=400,
                                     on_progress=_download_heartbeat(run, name))
            _set(run, checkpoint_local_path=dest,
                 phase_detail=f'Downloaded {os.path.basename(dest)}')
            return True
    except Exception as e:
        logger.warning('checkpoint download failed: %s', e)
    return bool(allow_stale and run.checkpoint_local_path
                and os.path.isfile(run.checkpoint_local_path))


def _import_result(run):
    """Copy the downloaded checkpoint into the ComfyUI loras folder when one
    is configured; otherwise it stays in staging (served by the download
    route). Import failure must not fail the run."""
    try:
        if not run.checkpoint_local_path:
            return
        if not (cfg.get('comfyui.base_dir') or cfg.get('comfyui.loras_dir')):
            return
        params = json.loads(run.train_params or '{}')
        lt.import_checkpoint('local', run.dataset_id,
                             os.path.basename(run.checkpoint_local_path),
                             base_model=params.get('base_model', ''),
                             family=params.get('train_type'),
                             src_dir=run.staging_dir,
                             version=params.get('version'),
                             variant=params.get('variant'),
                             run_id=run.id, run_source='cloud')
    except Exception as e:
        logger.warning('cloud import into ComfyUI failed: %s', e)


def _download_intermediates(run, remote):
    """After the FINAL checkpoint landed (strict path), also pull the pod's
    remaining intermediate saves — WITHOUT them a cloud run offered only its
    last epoch while a local run offers max_step_saves of them to pick the
    least-overfit one (user-observed parity gap, 2026-07-13). Best-effort per
    file: a failed intermediate never degrades the run's outcome."""
    try:
        files = [f for f in remote.list_files(run.remote_job_id)
                 if f.get('path', '').endswith('.safetensors')]
    except Exception as e:
        logger.warning('intermediate listing failed: %s', e)
        return
    have = os.path.basename(run.checkpoint_local_path or '')
    for f in files:
        name = os.path.basename(f['path'].replace('\\', '/'))
        if name == have:
            continue
        dest = os.path.join(run.staging_dir, name)
        want = int(f.get('size') or 0)
        try:
            if os.path.isfile(dest) and (not want or os.path.getsize(dest) == want):
                continue
            remote.download_public_file(f['path'], dest,
                                        expected_size=want or None, attempts=50)
        except Exception as e:
            logger.warning('intermediate %s not retrieved: %s', name, e)


def _mirror_into_local_run(run):
    """Copy the downloaded cloud checkpoints (final + retrieved intermediates)
    into the LOCAL ai-toolkit run dir, renamed to the local convention
    (`lora_<trigger>[_<step>].safetensors`), so cloud results behave exactly
    like local ones everywhere downstream: the panel's checkpoint list, the
    Resume-or-Fresh prompt, Continue training. No-op when ai-toolkit isn't
    configured locally; best-effort, never fails the run."""
    try:
        if not run.staging_dir or not os.path.isdir(run.staging_dir):
            return
        params = json.loads(run.train_params or '{}')
        # Mirror into THIS run's local dir: the stamped base ('' = official,
        # else the custom selection whose combo hash isolates the folder).
        run_dir = lt._run_dir('local', run.dataset_id,
                              base_model=params.get('base_model', ''),
                              family=params.get('train_type'),
                              variant=params.get('variant'))
        os.makedirs(run_dir, exist_ok=True)
        base = os.path.basename(os.path.normpath(run_dir))     # lora_<trigger>
        for src_name in sorted(os.listdir(run.staging_dir)):
            if not src_name.lower().endswith('.safetensors'):
                continue
            _mirror_one(run, run_dir, base, src_name)
    except Exception as e:
        # RuntimeError from _run_dir = ai-toolkit not configured -> fine
        logger.debug('local run-dir mirror skipped: %s', e)


def _mirror_one(run, run_dir, base, src_name):
    try:
        m = re.search(r'_(\d{6,})\.safetensors$', src_name)
        dest_name = f'{base}_{m.group(1)}.safetensors' if m else f'{base}.safetensors'
        dest = os.path.join(run_dir, dest_name)
        if os.path.exists(dest):
            # A LOCAL run of the same dataset+family already produced this
            # exact name (the unsuffixed FINAL collides whenever both worlds
            # completed a run) — never clobber local work. The cloud result
            # stays available in staging, ComfyUI and the hub's ⬇ button.
            logger.warning('local run dir already has %s — cloud mirror skipped '
                           '(local checkpoint left untouched)', dest_name)
            return
        shutil.copy2(os.path.join(run.staging_dir, src_name), dest)
        logger.info('mirrored cloud checkpoint into local run dir: %s/%s',
                    run_dir, dest_name)
    except (OSError, re.error) as e:
        logger.warning('mirror of %s skipped: %s', src_name, e)


def _cost_estimate(run) -> float:
    if not run.price_per_hour:
        return 0.0
    end = run.finished_at or datetime.utcnow()
    hours = max(0.0, (end - run.created_at).total_seconds() / 3600.0)
    return round(run.price_per_hour * hours, 2)


def month_spend_usd() -> float:
    """Total cost of the runs STARTED since the 1st of the current month
    (UTC). A run's cost = price_per_hour x (finished_at or now - created_at);
    runs that never got a priced pod (price_per_hour NULL) count for $0."""
    now = datetime.utcnow()
    month_start = datetime(now.year, now.month, 1)
    total = 0.0
    for r in (CloudTrainingRun.query
              .filter(CloudTrainingRun.created_at >= month_start).all()):
        if not r.price_per_hour or not r.created_at:
            continue
        end = r.finished_at or now
        total += r.price_per_hour * max(0.0, (end - r.created_at).total_seconds() / 3600.0)
    return total


def _dataset_name(dataset_id):
    """Human-readable dataset name for the cloud-runs hub — the run only stores
    dataset_id. Best-effort: a since-deleted dataset yields None, never a crash."""
    try:
        from ..models import FaceDataset
        ds = FaceDataset.query.get(dataset_id)
        return ds.name if ds is not None else None
    except Exception:
        return None


def _staging_save_count(run) -> int:
    """How many checkpoints (.safetensors) this run's staging currently holds —
    the 'saves' figure on the Runs-hub cards. 0 when staging is gone (purged /
    hand-deleted): the card simply drops the metric, never crashes."""
    if not run.staging_dir:
        return 0
    try:
        return sum(1 for f in os.listdir(run.staging_dir)
                   if f.lower().endswith('.safetensors'))
    except OSError:
        return 0


def _latest_sample_name(samples_dir):
    """Filename of the NEWEST sample image in a run's samples dir (highest
    step, then prompt index) or None. ai-toolkit names samples
    <ts>__<step>_<promptidx>.<ext> — lt._SAMPLE_RE parses that."""
    try:
        names = os.listdir(samples_dir)
    except OSError:
        return None
    best = None
    for f in names:
        m = lt._SAMPLE_RE.search(f)
        if not m:
            continue
        key = (int(m.group(1)), int(m.group(2)))
        if best is None or key > best[0]:
            best = (key, f)
    return best[1] if best else None


def _run_samples_dir(crun, rec):
    """Samples dir of a run — cloud: its staging download; local: the
    ai-toolkit run dir stamped on its registry row. None when unresolvable
    (purged staging, ai-toolkit not configured, deleted dataset)."""
    if crun is not None and crun.staging_dir:
        return os.path.join(crun.staging_dir, 'samples')
    if rec is not None and rec.source == 'local':
        try:
            return os.path.join(
                lt._run_dir(cfg.LOCAL_USER, rec.dataset_id,
                            base_model=rec.base_model or '',
                            family=rec.family, variant=rec.variant),
                'samples')
        except Exception:
            return None
    return None


def run_preview_path(run_key):
    """Absolute path of a run's newest sample image, or None — the Runs-hub
    card thumbnail. `run_key` is the run's share key ('cloud-<id>'/'rec-<id>',
    same addressing as the Share-config download). Resolved entirely
    server-side from the run's own rows: the client never sends a path."""
    from .run_share import resolve_run
    crun, rec = resolve_run(run_key)
    if crun is None and rec is None:
        return None
    d = _run_samples_dir(crun, rec)
    if not d:
        return None
    name = _latest_sample_name(d)
    if not name:
        return None
    p = os.path.join(d, name)
    return p if os.path.isfile(p) else None


def _annotate_preview(row, crun, rec):
    """Stamp `preview_url` on a Runs-hub history row when the run left at
    least one sample on disk — the frontend shows it as the card thumbnail
    (and falls back to a family tile when absent)."""
    d = _run_samples_dir(crun, rec)
    if d and _latest_sample_name(d):
        row['preview_url'] = f"/api/dataset/train/runs/{row['share_key']}/preview"


def _run_payload(run) -> dict:
    family = _run_family(run)
    variant = _run_param(run, 'variant')
    effective_base = _run_param(run, 'effective_base')
    training_adapter = _run_param(run, 'training_adapter')
    recipe_version = _run_param(run, 'recipe_version')
    # The base a run trained on ('' = official family base, else a custom
    # checkpoint/repo) — so the Runs-hub card can name it. Only merged when the
    # pod actually stamped it: absent on a very old pod stays out of the payload
    # (the card degrades to the family badge, never a wrong "official" claim),
    # and a registry-backed row keeps its own base_model through _run_payload's
    # enrichment update.
    base_model = _run_param(run, 'base_model')
    diagnostic = lt.zimage_recipe_diagnostic(
        family, variant, effective_base, training_adapter, recipe_version)
    payload = {'run_id': run.id, 'dataset_id': run.dataset_id, 'status': run.status,
            # Stable id for the per-run "Share configuration" download. Every
            # cloud row (active/finished/legacy) addresses by its pod row id;
            # local rows use 'rec-<record id>' (set in all_runs).
            'share_key': f'cloud-{run.id}',
            'run_name': run.run_name, 'dataset_name': _dataset_name(run.dataset_id),
            'vast_instance_id': run.vast_instance_id,   # for the per-run "console ↗" tooltip
            'phase_detail': run.phase_detail, 'gpu': run.gpu_name,
            'price_per_hour': run.price_per_hour,
            'cost_estimate': _cost_estimate(run), 'error': run.error,
            # isfile, not just a stored path: the user may delete staging
            # files by hand (Explorer) — a ready flag pointing at a missing
            # file yields a download button that 404s.
            'checkpoint_ready': bool(run.checkpoint_local_path
                                     and os.path.isfile(run.checkpoint_local_path)),
            # card metrics: target steps (stamped launch param) + how many
            # checkpoints the pod saved (live count of the staging downloads)
            'steps': _run_param(run, 'steps'),
            'saves': _staging_save_count(run),
            # Distinct steps of the harvested checkpoints still in staging — the
            # ▶ Continue dialog offers them so a finished run can resume from an
            # EARLIER epoch, not only its last (empty when staging was purged).
            'resume_steps': (sorted({c['step'] for c in _run_staging_checkpoints(run)})
                             if run.status == 'done' else []),
            'train_type': family, 'variant': variant,
            'effective_base': effective_base,
            'training_adapter': training_adapter,
            'recipe_version': recipe_version,
            'recipe_status': diagnostic and diagnostic.get('status'),
            'recipe_warning': diagnostic and diagnostic.get('warning'),
            'version': _run_param(run, 'version'),
            'auto_retry_count': int(_run_param(run, 'auto_retry_count') or 0),
            'auto_retry_of': _run_param(run, 'auto_retry_of'),
            'auto_retry_run_id': _run_param(run, 'auto_retry_run_id'),
            'created_at': run.created_at.isoformat() if run.created_at else None,
            # How long the run has reported nothing, and how long it is allowed
            # to (0 = the freeze watchdog is off). The card warns on its own
            # from these two, so a silent run is visible even when the watchdog
            # is configured never to cut.
            'idle_seconds': int(_idle_seconds(run)),
            'idle_limit_seconds': (_freeze_limit_seconds(run)
                                   if run.status in ACTIVE_STATES else 0),
            'stop_requested': bool(run.stop_requested_at),
            'finished_at': run.finished_at.isoformat() if run.finished_at else None}
    if base_model is not None:
        payload['base_model'] = base_model
    return payload


def cloud_status() -> dict:
    actives = get_active_runs()
    c = cfg.get('cloud') or {}
    limit = max(1, int((c.get('max_concurrent_runs') or 1)))
    last = (CloudTrainingRun.query
            .order_by(CloudTrainingRun.id.desc()).first())
    return {'configured': bool(cfg.secret('VAST_API_KEY')), 'limit': limit,
            'actives': [_run_payload(r) for r in actives],
            # compat: single 'active' field for old frontend/tests, first of actives
            'active': _run_payload(actives[0]) if actives else None,
            'total_price_per_hour': round(sum(r.price_per_hour or 0 for r in actives), 4),
            # budget guardrails: what this month already cost, the configured
            # ceiling (0 = unlimited), and the runtime cap the frontend uses
            # for its worst-case cost estimate.
            'month_spend': round(month_spend_usd(), 2),
            'monthly_budget': float(c.get('monthly_budget_usd') or 0),
            'max_runtime_minutes': int(c.get('max_runtime_minutes') or 480),
            'last': _run_payload(last) if last else None}


def all_runs(limit: int = 20) -> dict:
    """Everything the unified Runs hub needs in one call: the active cloud
    runs (manage/watch), the LIVE local training if any, and a history of
    EVERY launch — local AND cloud — from the provenance registry (each row
    carries the settings snapshot the launch actually sent to ai-toolkit).
    Cloud rows are enriched from their CloudTrainingRun (status/cost/
    checkpoint); cloud runs that predate the registry still appear via a
    fallback union, so history never shrinks."""
    from ..models import TrainingRunRecord
    actives = get_active_runs()
    c = cfg.get('cloud') or {}
    limit = max(1, min(int(limit or 20), 100))
    recs = (TrainingRunRecord.query
            .order_by(TrainingRunRecord.id.desc()).limit(limit).all())
    cloud_ids = {r.cloud_run_id for r in recs if r.cloud_run_id}
    cloud_by_id = ({r.id: r for r in CloudTrainingRun.query
                    .filter(CloudTrainingRun.id.in_(cloud_ids)).all()}
                   if cloud_ids else {})
    # Local runs have no status column — the failed one (at most a single row,
    # local training is single-flight) is derived from the transient crash state
    # so its row can carry status='error' + a ↻ Retry affordance.
    _failed_local = lt.failed_local_run()
    failed_local_id, failed_local_msg = _failed_local or (None, None)
    recent = []
    for rec in recs:
        crun = cloud_by_id.get(rec.cloud_run_id)
        if crun is not None and crun.status in ACTIVE_STATES:
            continue                      # already shown in the actives section
        try:
            settings = json.loads(rec.settings) if rec.settings else None
        except ValueError:
            settings = None
        row = {'source': 'cloud' if rec.source == 'cloud' else 'local',
               'dataset_id': rec.dataset_id,
               'dataset_name': _dataset_name(rec.dataset_id),
               'train_type': rec.family, 'version': rec.version,
               'steps': rec.steps, 'masked': bool(rec.masked),
               'variant': rec.variant, 'base_model': rec.base_model or '',
               'settings': settings,
               # Lineage edge (genealogy tree): the record this launch resumed
               # from, NULL on a fresh run / root. `lineage` (below) then flags
               # rows that open into a ≥2-node tree.
               'parent_record_id': rec.parent_record_id,
               'resumed_from': rec.resumed_from,
               # Stable local-run identity for the 💻 #N chip + Checkpoints
               # deep-link. Cloud rows show ☁ #<cloud run id> (run_id, below).
               'record_id': rec.id,
               # local rows live only in the registry -> addressed by record id;
               # a cloud row overrides this with 'cloud-<id>' via _run_payload.
               'share_key': f'rec-{rec.id}',
               # Stable retry target for a LOCAL run (cloud rows retry by run_id).
               'record_id': rec.id,
               'created_at': rec.created_at.isoformat() if rec.created_at else None}
        if rec.source == 'local' and rec.id == failed_local_id:
            row['status'] = 'error'
            row['error'] = failed_local_msg
        if rec.family == 'zimage':
            safe_settings = settings if isinstance(settings, dict) else {}
            diag = lt.zimage_recipe_diagnostic(
                rec.family, rec.variant,
                safe_settings.get('effective_base'),
                safe_settings.get('training_adapter'),
                safe_settings.get('recipe_version'))
            row.update({'effective_base': safe_settings.get('effective_base'),
                        'training_adapter': safe_settings.get('training_adapter'),
                        'recipe_version': safe_settings.get('recipe_version'),
                        'recipe_status': diag and diag.get('status'),
                        'recipe_warning': diag and diag.get('warning')})
        if crun is not None:
            # cloud enrichment wins on shared keys (status/cost/checkpoint/...)
            # — except steps, where the registry row must survive a pod row
            # whose train_params never stamped them (payload steps = None).
            registry_steps = row.get('steps')
            row.update(_run_payload(crun))
            if row.get('steps') is None:
                row['steps'] = registry_steps
            row['settings'] = settings
            row['source'] = 'cloud'
        _annotate_preview(row, crun, rec)
        recent.append(row)
    # Legacy cloud runs that predate the provenance registry (no record row).
    seen_cloud = {r.get('run_id') for r in recent if r.get('run_id')}
    for crun in (CloudTrainingRun.query
                 .filter(CloudTrainingRun.status.notin_(ACTIVE_STATES))
                 .order_by(CloudTrainingRun.id.desc()).limit(limit).all()):
        if crun.id in seen_cloud:
            continue
        row = {'source': 'cloud', 'settings': None, **_run_payload(crun)}
        _annotate_preview(row, crun, None)
        recent.append(row)
    # Lineage flag: a row opens the 🌳 tree when it has a parent OR is itself a
    # parent (a continuation branched off it). `records_with_children` is one
    # query over the shown record ids, so a parent still flags even when its
    # child sits outside this window.
    from . import checkpoint_registry
    _rec_ids = [r['record_id'] for r in recent if r.get('record_id')]
    _parents = checkpoint_registry.records_with_children(_rec_ids)
    for r in recent:
        r['lineage'] = bool(r.get('parent_record_id')
                            or (r.get('record_id') in _parents))
    recent.sort(key=lambda r: r.get('created_at') or '', reverse=True)
    recent = recent[:limit]
    # Live LOCAL training: shown as its own card next to the cloud actives;
    # its freshly-registered history row is dropped to avoid the double.
    local = lt.training_status()
    local_active = local if local.get('in_progress') else None
    if local_active and (local.get('current') or {}).get('dataset_id') is not None:
        cur_ds = local['current']['dataset_id']
        for i, r in enumerate(recent):
            if r['source'] == 'local' and r['dataset_id'] == cur_ds:
                # its freshly-registered history row is dropped to avoid the
                # double — carry its share_key (Share config) AND record_id
                # (💻 #N chip) onto the live card.
                dropped = recent.pop(i)
                local_active['share_key'] = dropped.get('share_key')
                local_active['record_id'] = dropped.get('record_id')
                break
    return {'configured': bool(cfg.secret('VAST_API_KEY')),
            'limit': max(1, int((c.get('max_concurrent_runs') or 1))),
            'actives': [_run_payload(r) for r in actives],
            'local_active': local_active,
            'recent': recent,
            'total_price_per_hour': round(sum(r.price_per_hour or 0 for r in actives), 4),
            'month_spend': round(month_spend_usd(), 2),
            'monthly_budget': float(c.get('monthly_budget_usd') or 0)}


def _checkpoint_download_url(dataset_id, source, run_id, filename,
                            family=None, variant=None, base_model=None):
    """The EXISTING browser-download endpoint for one saved checkpoint, so the
    ◉ Graph's per-checkpoint ⬇ reuses the same serving path as the Runs hub /
    Checkpoints panel instead of a parallel one. Cloud saves stream from the
    run's staging dir (train/cloud/checkpoint, extended with ?filename); local
    saves from the run dir (train/checkpoint/file). Query values are url-encoded
    so a trigger with odd characters can't break the link."""
    from urllib.parse import quote
    if source == 'cloud':
        return (f'/api/dataset/{dataset_id}/train/cloud/checkpoint'
                f'?run_id={run_id}&filename={quote(filename)}')
    qs = [f'filename={quote(filename)}']
    if family:
        qs.append(f'train_type={quote(str(family))}')
    if variant:
        qs.append(f'variant={quote(str(variant))}')
    if base_model:
        qs.append(f'base_model={quote(str(base_model))}')
    return f'/api/dataset/{dataset_id}/train/checkpoint/file?' + '&'.join(qs)


def _node_checkpoints(rec, crun):
    """Every save this ONE run produced, as compact nodes for the ◉ Graph: a
    step-sorted list of {step, filename, final, present, download_url}. Cloud
    runs read their harvested staging saves; local runs read the run-dir files
    list_checkpoints already attributes to this record. `present` is True for a
    listed file (it is on disk); a run whose saves are all gone simply lists
    none. Best-effort — a failed scan yields [] (the node shows no pills), never
    a wrong claim. Mirrors the Runs-hub / Checkpoints-panel step extraction so a
    pill's step is exactly what 'continue from here' resumes."""
    out = []
    if crun is not None:
        for c in _run_staging_checkpoints(crun):
            final = not re.search(r'_(\d{6,})\.safetensors$', c['filename'])
            out.append({
                'step': c['step'], 'filename': c['filename'],
                'final': bool(final and crun.status == 'done'), 'present': True,
                'download_url': _checkpoint_download_url(
                    rec.dataset_id, 'cloud', crun.id, c['filename'])})
        return out
    # Local: list_checkpoints may raise if ai-toolkit isn't configured — let it
    # propagate so the caller can tell "scan failed" (None) from "no saves" ([]).
    cks = lt.list_checkpoints(cfg.LOCAL_USER, rec.dataset_id,
                              rec.base_model or '', rec.family, rec.variant)
    for c in cks:
        if c.get('run_source') != 'local' or c.get('run_id') != rec.id:
            continue
        out.append({
            'step': c['step'], 'filename': c['filename'],
            'final': bool(c.get('final')), 'present': True,
            'download_url': _checkpoint_download_url(
                rec.dataset_id, 'local', rec.id, c['filename'],
                family=rec.family, variant=rec.variant, base_model=rec.base_model)})
    return out


def _rec_config(rec):
    """The settings the run actually used, for the Lab inspector. None (not {})
    when a run recorded nothing (legacy) so the UI can say 'config not recorded'
    instead of showing an empty table."""
    if not rec.settings:
        return None
    try:
        cfg = json.loads(rec.settings)
        return cfg if isinstance(cfg, dict) else None
    except (ValueError, TypeError):
        return None


def set_run_note(record_id, text):
    """Save the free-form Lab note on a run. False (no-op) if the record is gone."""
    from ..models import TrainingRunRecord
    from ..extensions import db
    rec = TrainingRunRecord.query.get(record_id)
    if rec is None:
        return False
    rec.note = text or ''
    db.session.commit()
    return True


def set_checkpoint_note(record_id, step, text):
    """Save the free-form Lab note on one checkpoint (record_id, step). False if
    the owning run is gone."""
    from ..models import TrainingRunRecord, CheckpointNote
    from ..extensions import db
    if TrainingRunRecord.query.get(record_id) is None:
        return False
    row = CheckpointNote.query.filter_by(record_id=record_id, step=step).first()
    if row is None:
        row = CheckpointNote(record_id=record_id, step=step)
        db.session.add(row)
    row.note = text or ''
    db.session.commit()
    return True


def checkpoint_notes_for(record_id):
    """{step: note} for a run's annotated checkpoints (empty notes omitted)."""
    from ..models import CheckpointNote
    return {r.step: r.note for r in
            CheckpointNote.query.filter_by(record_id=record_id).all()
            if r.note}


def training_activity() -> dict:
    """🏋️ Is anything training RIGHT NOW — locally or on a rented pod.

    Deliberately the cheapest question the app can ask: one persisted flag plus
    one indexed COUNT. No capability probe, no disk, no network — the nav bar
    polls this from every page, so it has to stay free. `cloud` is a count
    because several pods can train at once; `local` is a boolean because local
    training is single-flight."""
    cloud = (CloudTrainingRun.query
             .filter(CloudTrainingRun.status.in_(ACTIVE_STATES)).count())
    local = training_in_progress()
    return {'local': local, 'cloud': cloud, 'running': bool(local or cloud)}


def training_in_progress() -> bool:
    """True while a LoRA training holds the GPU — the Lab's inline generation is
    refused with a 409 in that window (a training and a generation must never
    share the GPU). Reads the same persisted flag the queue and the vision window
    check, so all three agree on 'GPU held by training'."""
    from ..job_queue import queue_manager
    return bool(queue_manager._get_system_state('training_in_progress', False))


# --- Lab inline previews (D) -------------------------------------------------
# The flagship: render ONE same-prompt/same-seed image per selected lineage
# checkpoint, reusing the EXISTING Test-Studio ComfyUI engine pinned to those
# checkpoints at strength 1.0 (not a checkpoint×strength grid). A checkpoint is
# "testable" only when its step has a matching DEPLOYED LoRA in the family pool
# (the same pool the Studio tests) — otherwise there is nothing ComfyUI can load,
# so we say "not deployed" instead of launching a silent no-op.

def _step_of_testable(filename) -> int | None:
    """The training step embedded in a deployed testable LoRA filename, so a
    lineage pill (which carries its own step) can be joined to the deployed LoRA
    of the same step. ai-toolkit deploys the step ZERO-PADDED IN THE MIDDLE, e.g.
    'lora_morgot_cv_000001500_Krea-2-Raw_rc74_v3' (step 1500) — not at the end, so
    an end-anchored match misses every real checkpoint. Match the zero-padded run
    first (unambiguous: base/rc/version tokens aren't zero-padded), then fall back
    to a plain step at the very end ('<trigger>-<step>' / 'lora_<trigger>_<step>').
    A final save with no number yields None (matched by step only)."""
    stem = os.path.basename(str(filename or '')).rsplit('.', 1)[0]
    if stem.lower().startswith('lora_'):
        stem = stem[5:]
    # Zero-padded step anywhere in the name (leading 0, ≥4 digits) — this is the
    # ai-toolkit convention and never collides with 'Krea-2-Raw'/'rc74'/'v3'.
    m = re.search(r'[-_](0\d{3,})(?=[-_]|$)', stem)
    if not m:
        m = re.search(r'[-_](\d+)$', stem)   # legacy: plain step at the end
    return int(m.group(1)) if m else None


def _deployed_run_tag(rec):
    """(source, run_id) as it appears in the DEPLOYED names of THIS record's
    saves. Mirrors import_checkpoint's own rule: a cloud launch is tagged with
    its pod-run id (`_rc<id>`, the ☁ #N chip), everything else with its
    TrainingRunRecord id (`_rl<id>`). (None, None) when a cloud record lost its
    pod-run id — no tag to match, so nothing is claimed."""
    if rec.source == 'cloud':
        return ('cloud', rec.cloud_run_id) if rec.cloud_run_id else (None, None)
    return 'local', rec.id


def _final_step_of(checkpoints) -> int | None:
    """The step of a run's FINAL save among its listed pills: the one flagged
    `final`, else the largest step (a run whose final save exists but isn't
    flagged — cloud runs only flag it once the run is 'done'). None when the run
    lists no save."""
    for c in (checkpoints or []):
        if c.get('final') and c.get('step') is not None:
            return c['step']
    return max((c['step'] for c in (checkpoints or [])
                if c.get('step') is not None), default=None)


def _deploy_version(filename) -> int:
    """The `_v<N>` dataset-version suffix of a deployed name (0 when absent) —
    used only to pick deterministically between several step-less deploys of the
    SAME run (the newest version wins; a plain name sort would rank `_v10` under
    `_v9`)."""
    stem = os.path.basename(str(filename or '')).rsplit('.', 1)[0]
    m = re.search(r'_v(\d+)$', stem)
    return int(m.group(1)) if m else 0


def _deletable_deploy_names(dataset_id, family) -> dict:
    """{lowercased basename: filename as delete_imported_checkpoint whitelists it}
    for this dataset+family. The testable map names the deployed LoRA as the
    ComfyUI POOL sees it, while the deployed-delete route whitelists the names
    `list_imported_checkpoints` scans off disk — the same files, but the two
    forms can differ (path separator, subfolder prefix). Joining on the basename
    gives the UI a delete target the route will actually accept, instead of a
    name that resolves to 'unknown checkpoint'. Best-effort: {} on any failure,
    so a pill simply offers no deployed-delete rather than a doomed button."""
    try:
        rows = lt.list_imported_checkpoints(cfg.LOCAL_USER, dataset_id, family=family)
    except Exception:
        return {}
    out = {}
    for r in rows:
        fn = str(r.get('filename') or '')
        if fn:
            out[os.path.basename(fn.replace('\\', '/')).lower()] = fn
    return out


def _testable_by_step(dataset_id, family, run_tag=None, final_step=None) -> dict:
    """{step: deployed_lora_filename} for this dataset+family — the checkpoints
    the Lab can actually generate a preview for. Best-effort: no dataset / no
    deployed LoRA → {} (every pill reads as not-testable, the Generate button
    stays disabled with the app's usual 'needs setup' hint).

    `run_tag`/`final_step` (one run's identity + its last step) additionally join
    that run's STEP-LESS deploy: ai-toolkit names the final save without a step
    (`lora_nova_Krea-2-Raw_rc90_v2`), so it has no number to be matched by and the
    final pill never gained a tick-box even once imported (user-reported on two
    runs). The run tag baked into the deployed name (`_rc<id>`/`_rl<id>`, see
    lt.parse_deployed_run) is what attaches it to its run. A legacy untagged file
    stays unmatched — better no tick-box than one on another run's checkpoint."""
    ds = fds.get_dataset(cfg.LOCAL_USER, dataset_id)
    if not ds:
        return {}
    from . import lora_test_studio as studio
    out, stepless = {}, []
    try:
        cands = studio.list_test_checkpoints(ds, family)
    except Exception:
        return {}
    for c in cands:
        fn = c['filename']
        s = _step_of_testable(fn)
        if s is not None:
            # A NUMBERED save must belong to the run we are answering for.
            # Without this, two runs of the same dataset+family that both saved
            # at step 2500 shared one key: importing run A's 2500 lit up "✓
            # Deployed" on run B's 2500 too, and B's Undeploy would have removed
            # A's file. Reported after importing step 2500 of one run and seeing
            # every other run's 2500 turn green.
            # Untagged files (imported before run tagging) still match on the
            # step alone — refusing them would un-deploy every legacy import.
            if run_tag and run_tag[1]:
                tag = lt.parse_deployed_run(fn)
                if tag[1] is not None and tag != tuple(run_tag):
                    continue
            out[s] = fn
        else:
            stepless.append(fn)
    # Deterministic on collision: a file that NAMES the step always wins over a
    # step-less one claiming the same step, and among several step-less deploys
    # of the same run the highest `_v<N>` wins.
    if stepless and run_tag and run_tag[1] and final_step is not None \
            and final_step not in out:
        mine = [f for f in stepless if lt.parse_deployed_run(f) == tuple(run_tag)]
        if mine:
            out[final_step] = max(mine, key=lambda f: (_deploy_version(f), f))
    return out


def _testable_for_record(dataset_id, family, record_id) -> dict:
    """{step: deployed filename} as seen FROM one run — the dataset+family map
    plus that run's own step-less final save (see _testable_by_step). Degrades to
    the plain map when the record is unknown or its save list can't be read."""
    from ..models import TrainingRunRecord
    rec = db.session.get(TrainingRunRecord, record_id)
    if rec is None:
        return _testable_by_step(dataset_id, family)
    crun = (db.session.get(CloudTrainingRun, rec.cloud_run_id)
            if rec.cloud_run_id else None)
    try:
        cks = _node_checkpoints(rec, crun)
    except Exception:
        cks = []
    return _testable_by_step(dataset_id, family, run_tag=_deployed_run_tag(rec),
                             final_step=_final_step_of(cks))


def checkpoint_previews_for(record_id) -> dict:
    """{step: {status, url, seed, count}} for a run's checkpoints. Each stored
    pointer resolves LIVE to its reused LoraTestImage: 'done' with a served url
    once the file exists, 'failed' if the cell failed, else 'pending' (the job is
    still in the serial queue). A dangling pointer (image row gone) is dropped so
    the node never claims a preview it can't show.

    Previews ACCUMULATE, so a checkpoint can hold several rows: the NEWEST one
    that still resolves is the thumbnail. `count` is not that list's length — it
    counts every finished test image linked to the checkpoint, wherever it came
    from (Test Studio, canvas, comparison grid), which is what the gallery under
    the node opens on."""
    from ..models import CheckpointPreview, LoraTestImage
    # Newest first, so the first resolvable row per step is the one shown.
    rows = (CheckpointPreview.query.filter_by(record_id=record_id)
            .order_by(CheckpointPreview.id.desc()).all())
    counts = dict(db.session.query(LoraTestImage.step, func.count(LoraTestImage.id))
                  .filter(LoraTestImage.record_id == record_id,
                          LoraTestImage.status == 'done',
                          LoraTestImage.filename.isnot(None))
                  .group_by(LoraTestImage.step).all())
    if not rows and not counts:
        return {}
    img_ids = [r.lora_test_image_id for r in rows if r.lora_test_image_id]
    imgs = ({i.id: i for i in LoraTestImage.query
             .filter(LoraTestImage.id.in_(img_ids)).all()} if img_ids else {})
    out = {}
    for r in rows:
        if r.step in out:
            continue                      # an older preview of the same checkpoint
        img = imgs.get(r.lora_test_image_id)
        if img is None:
            continue
        status = img.status if img.status in ('pending', 'done', 'failed') else 'pending'
        url = (f'/api/dataset/{r.dataset_id}/img/{img.filename}'
               if status == 'done' and img.filename else None)
        out[r.step] = {'status': status, 'url': url, 'seed': r.seed,
                       'count': int(counts.get(r.step) or 0)}
    # A checkpoint generated from the Test Studio has images but never a preview
    # pointer. It still has a gallery — the node must say so.
    for step, n in counts.items():
        if step is None or step in out:
            continue
        out[step] = {'status': None, 'url': None, 'seed': None, 'count': int(n)}
    return out


def canvas_generate(user_id, selections, **knobs) -> dict:
    """◉ Launch from the LoRA Canvas: the EXACT Test-Studio engine, told which
    checkpoints to run by the pills the user ticked instead of by a picker.

    `selections` = [{dataset_id, checkpoint, record_id, step}] — possibly across
    SEVERAL datasets, which is the point of the canvas
    (``LoraTestImage.run_id`` has always grouped cells of different datasets).
    Every other setting rides through untouched to ``create_comparison_run``,
    because it IS the same call the comparison grid makes: no second engine, so
    no drift between the two screens.

    Mixing FAMILIES is refused by the engine itself (one run = one base + one
    workflow) and the message travels back to the button.

    After the cells are created, one ``CheckpointPreview`` per distinct
    (record, step) points the node at what it just launched, so the pill shows
    ◌ rendering and then the picture. It is an INSERT, not an update: previews
    accumulate, and the older ones stay in the checkpoint's gallery."""
    from ..models import CheckpointPreview, LoraTestImage
    from . import lora_test_studio as studio

    res = studio.create_comparison_run(user_id, selections, **knobs)
    ids = res.get('ids') or []
    if ids:
        rows = LoraTestImage.query.filter(LoraTestImage.id.in_(ids)).all()
        seen = set()
        # Ordered by id so "the preview" is the first cell of the launch, a
        # stable choice rather than whatever the query happened to return first.
        for row in sorted(rows, key=lambda r: r.id):
            if row.record_id is None or row.step is None:
                continue                  # an unattributed pick has no node to sit under
            key = (row.record_id, row.step)
            if key in seen:
                continue
            seen.add(key)
            db.session.add(CheckpointPreview(
                record_id=row.record_id, step=row.step, dataset_id=row.dataset_id,
                lora_test_image_id=row.id, prompt=row.prompt or '', seed=row.seed))
        db.session.commit()
    return res


def checkpoint_gallery(record_id, step, limit=120) -> dict:
    """Every finished image this checkpoint ever produced, newest first — the
    gallery the canvas opens under a node.

    The source is the LINK written at generation time
    (``lora_test_image.record_id`` / ``.step``), so it holds whatever made the
    image: an inline canvas preview, a Test-Studio grid cell, a comparison run.
    Nothing is parsed out of a filename here — that is the whole point of the
    columns.

    `unlinked` is the honest footnote: images that exist but carry no link (they
    predate the columns and their filename did not attribute itself). They are
    NOT shown under a checkpoint they might not belong to; the number is
    reported so the gap is stated instead of looking like an empty history."""
    from ..models import LoraTestImage
    q = (LoraTestImage.query
         .filter(LoraTestImage.record_id == record_id,
                 LoraTestImage.step == step,
                 LoraTestImage.status == 'done',
                 LoraTestImage.filename.isnot(None))
         .order_by(LoraTestImage.id.desc()))
    total = q.count()
    rows = q.limit(max(1, min(int(limit or 120), 500))).all()
    from .checkpoint_link_backfill import unlinked_count
    from . import trash
    return {
        'record_id': record_id, 'step': step, 'count': total,
        'unlinked': unlinked_count(),
        # Where a deleted image WOULD land, resolved the same way the deletion
        # resolves it, so the confirmation never promises the wrong thing.
        'delete_mode': trash.disposal_mode(),
        'images': [_gallery_image(r) for r in rows],
    }


def _gallery_image(r) -> dict:
    """One image row as the galleries publish it. Extracted so the checkpoint
    gallery and the run gallery can never drift into two shapes — the panel is
    ONE component and it reads these keys."""
    return {
        'id': r.id,
        'dataset_id': r.dataset_id,
        'url': f'/api/dataset/{r.dataset_id}/img/{r.filename}',
        'rating': r.rating,
        'prompt': r.prompt,
        'seed': r.seed,
        'strength': r.strength,
        'step': r.step,
        # WHICH checkpoint made it. Redundant inside a checkpoint gallery (the
        # scope already says so) and load-bearing outside one: a pinned canvas
        # node draws its link to the source pill from these two, so the link
        # cannot drift from the image.
        'record_id': r.record_id,
        'created_at': r.created_at.isoformat() if r.created_at else None,
        # ── What the image was actually MADE with ────────────────────────────
        # Every one of these was already persisted per cell (for a faithful
        # resume) and none of it reached the viewer, which on a board whose
        # whole job is comparing checkpoints is the wrong half to hide: two
        # renders that differ only by sampler or CFG look like a checkpoint
        # difference until you can read the settings. Nothing new is computed
        # here — these are columns, published.
        'checkpoint': r.checkpoint,
        'base_model': r.z_model,
        'negative': r.negative,
        'cfg': r.cfg,
        'steps': r.steps,
        'sampler': r.sampler,
        'scheduler': r.scheduler,
        'aspect': r.aspect,
        'extra_loras': r.extra_loras,
        'face_score': r.face_score,
    }


# How many images ONE step contributes to a run gallery, and how many the whole
# answer may carry. A run with 14 checkpoints × every render it ever got is a
# payload nobody reads and a grid that stutters on a phone; a per-step slice
# keeps every checkpoint represented instead of letting the newest one eat the
# whole budget. Both caps are REPORTED (`truncated`), never silent.
RUN_GALLERY_PER_STEP = 30
RUN_GALLERY_LIMIT = 240


def run_gallery(record_id, limit=RUN_GALLERY_LIMIT,
                per_step=RUN_GALLERY_PER_STEP) -> dict:
    """Everything ONE RUN ever produced, grouped by the checkpoint that made it —
    the gallery the ◉ Canvas opens on a run card.

    Same link, same rows and the same delete as ``checkpoint_gallery``: this is
    the checkpoint gallery with its scope widened, not a second reader. A run's
    images are the union of its checkpoints' images, so two independent readers
    would be two chances to disagree about what exists.

    Order: **steps descending**, the most-trained checkpoint first. The pill row
    on the board already reads left-to-right in training order; what the panel is
    for is judging where the LoRA stopped getting better, and that judgement
    starts at the end. Inside a step the app's rule is unchanged — newest first.

    ``step: null`` is a real group, LAST: images attributable to this RUN but not
    to a step (a step-less final save carries the run tag in its name and no
    step). They used to be counted as "not traced back to a checkpoint", which
    was true and useless — the run is knowable, so it is stated.

    Counts are exact; the IMAGES are capped per step and overall, and each group
    says whether it was cut (`truncated`). `count` is always the run's real
    total.

    The checkpoint NOTES ride along, read from ``checkpoint_note`` rather than
    from the pills: a note is keyed by (record_id, step) and outlives the file it
    describes, so a run whose saves have been cleaned off the disk would
    otherwise show its images and silently lose what was written about them."""
    from ..models import CheckpointNote, LoraTestImage
    from .checkpoint_link_backfill import unlinked_count
    from . import trash

    base = LoraTestImage.query.filter(
        LoraTestImage.record_id == record_id,
        LoraTestImage.status == 'done',
        LoraTestImage.filename.isnot(None))
    counted = (db.session.query(LoraTestImage.step, func.count(LoraTestImage.id))
               .filter(LoraTestImage.record_id == record_id,
                       LoraTestImage.status == 'done',
                       LoraTestImage.filename.isnot(None))
               .group_by(LoraTestImage.step).all())
    # Steps descending, the step-less group last — sorted here rather than in SQL
    # because NULL ordering is dialect-dependent and this list is a handful long.
    order = sorted(((s, n) for s, n in counted),
                   key=lambda t: (t[0] is None, -(t[0] or 0)))

    notes = {n.step: (n.note or '').strip()
             for n in CheckpointNote.query.filter_by(record_id=record_id).all()
             if (n.note or '').strip()}
    cap = max(1, min(int(limit or RUN_GALLERY_LIMIT), 800))
    per = max(1, min(int(per_step or RUN_GALLERY_PER_STEP), cap))
    groups, shown, total = [], 0, 0
    for step, n in order:
        total += n
        room = max(0, cap - shown)
        take = min(per, n, room)
        rows = []
        if take:
            q = base.filter(LoraTestImage.step.is_(None) if step is None
                            else LoraTestImage.step == step)
            rows = q.order_by(LoraTestImage.id.desc()).limit(take).all()
            shown += len(rows)
        groups.append({
            'step': step, 'count': n,
            'truncated': len(rows) < n,
            'note': notes.get(step) or '',
            'images': [_gallery_image(r) for r in rows],
        })
    return {
        'record_id': record_id, 'count': total, 'shown': shown,
        # Every checkpoint note of the run, including the steps that produced no
        # image at all — those have no group to hang off, and a note nobody can
        # read is a note that was lost.
        'checkpoint_notes': [{'step': s, 'note': notes[s]}
                             for s in sorted(notes, reverse=True)],
        'truncated': shown < total,
        'per_step': per, 'limit': cap,
        # The honest footnote stays: images that carry no link AT ALL, not even a
        # run. Widening the scope must not make that number disappear.
        'unlinked': unlinked_count(),
        'delete_mode': trash.disposal_mode(),
        'groups': groups,
    }


def delete_checkpoint_images(record_id, step, image_ids) -> dict:
    """🗑 Delete generated images from a checkpoint's gallery — file AND row.

    These rows ARE the Test Studio's cells: one image lives in exactly one place
    in the database and is shown by two surfaces. So "remove it from this
    gallery" and "delete it" cannot both be true, and hiding it here while it
    stays in the Studio grid would only move the confusion. The gallery deletes
    for real, and the confirmation says the Test Studio loses them too — the
    consequence is stated BEFORE the click, not discovered after it.

    Nothing is destroyed outright: the file goes through ``trash.dispose`` (OS
    recycle bin → the app's own trash → a permanent unlink only if both refuse),
    exactly like the bank's rejected sweep. ``checkpoint_gallery`` reports the
    mode up front and this returns the mode actually used.

    Scoped to the checkpoint: an id that is not linked to (record_id, step) is
    refused, so this route cannot be turned into "delete any image by id".

    ``step=None`` widens the scope to the WHOLE RUN — every step of it plus the
    step-less group — which is what the run gallery deletes with. It is the same
    function on purpose: two delete paths over the same rows would be two places
    to keep the recycle-bin promise, the shared-file rule and the "generating is
    never cancelled" rule true, and they would drift.

    Degrades instead of failing, because the gallery of a real install is never
    tidy:
      • a row still generating keeps its file (skipped 'generating') — cancelling
        someone's running job is not what a delete click asked for;
      • a row whose file is already gone from disk still loses its row;
      • a file another surviving row also points at is unlinked from THIS row but
        left on disk (no surface loses a picture it still lists);
      • a file that cannot be moved keeps its row, so it stays visible and
        retryable rather than vanishing from the UI while it sits on disk.

    ``CheckpointPreview`` rows pointing at a deleted image are removed in the
    same transaction. The reader already drops a dangling pointer, but leaving
    one behind means a checkpoint silently falls back to an older preview with no
    trace of why — and the row would outlive every image it could ever resolve.

    Returns {'mode', 'deleted', 'trashed', 'already_absent', 'rows_removed',
    'previews_removed', 'dataset_ids', 'skipped': [{'id', 'reason'}]}."""
    from ..models import CheckpointPreview, LoraTestImage
    from . import trash
    wanted = []
    for i in (image_ids or []):
        try:
            wanted.append(int(i))
        except (TypeError, ValueError):
            continue
    out = {'mode': None, 'deleted': 0, 'trashed': 0, 'already_absent': 0,
           'rows_removed': 0, 'previews_removed': 0, 'dataset_ids': [],
           'skipped': []}
    if not wanted:
        return out
    scoped = LoraTestImage.query.filter(LoraTestImage.record_id == record_id,
                                        LoraTestImage.id.in_(wanted))
    if step is not None:
        scoped = scoped.filter(LoraTestImage.step == step)
    rows = scoped.all()
    found = {r.id for r in rows}
    for i in wanted:
        if i not in found:
            # Either a stale gallery (already deleted elsewhere) or an id that
            # belongs to another checkpoint. Same answer: not ours to delete.
            out['skipped'].append({'id': i, 'reason': 'not_in_gallery'})

    # A file can be pointed at by more than one row (a preview reuses an existing
    # cell). Only unlink from disk what nothing else still lists.
    keys = {(r.dataset_id, r.filename) for r in rows if r.filename}
    still_used = set()
    if keys:
        others = (LoraTestImage.query
                  .filter(LoraTestImage.dataset_id.in_({k[0] for k in keys}),
                          LoraTestImage.filename.in_({k[1] for k in keys}),
                          LoraTestImage.id.notin_(list(found))).all())
        still_used = {(o.dataset_id, o.filename) for o in others}

    remove_ids, modes_used, datasets = [], set(), set()
    disposed = set()                       # (dataset_id, filename) done this pass
    for row in rows:
        if row.status not in ('done', 'failed', 'cancelled'):
            out['skipped'].append({'id': row.id, 'reason': 'generating'})
            continue
        datasets.add(row.dataset_id)
        if not row.filename:
            # A failed/cancelled cell never wrote a file: only the row goes.
            remove_ids.append(row.id)
            continue
        key = (row.dataset_id, row.filename)
        path = os.path.join(fds._dataset_path(row.dataset_id), row.filename)
        if key in still_used or key in disposed:
            remove_ids.append(row.id)      # someone else still shows this picture
            continue
        if not os.path.exists(path):
            out['already_absent'] += 1
            remove_ids.append(row.id)
            continue
        try:
            mode = trash.dispose(path, context=(f'run-{record_id}' if step is None
                                                else f'checkpoint-{record_id}-{step}'))
        except OSError as e:
            out['skipped'].append({'id': row.id, 'reason': str(e)})
            continue
        disposed.add(key)
        modes_used.add(mode)
        if mode == 'delete':
            out['deleted'] += 1
        else:
            out['trashed'] += 1            # OS trash or app trash — recoverable
        remove_ids.append(row.id)

    if remove_ids:
        out['previews_removed'] = CheckpointPreview.query.filter(
            CheckpointPreview.lora_test_image_id.in_(remove_ids)
        ).delete(synchronize_session=False)
        LoraTestImage.query.filter(
            LoraTestImage.id.in_(remove_ids)).delete(synchronize_session=False)
        out['rows_removed'] = len(remove_ids)
        db.session.commit()
    out['dataset_ids'] = sorted(datasets)
    # Report the WORST outcome: one permanently removed file makes the whole run
    # 'delete', whatever the rest did. The UI wording follows this.
    for mode in ('delete', 'app_trash', 'trash'):
        if mode in modes_used:
            out['mode'] = mode
            break
    return out


def generate_checkpoint_previews(user_id, dataset_id, checkpoints, prompt=None,
                                 seed=None, family=None) -> dict:
    """Point the EXISTING Test-Studio engine at the selected lineage checkpoints,
    each at strength 1.0, with ONE shared prompt+seed — a same-conditions look at
    how the LoRA evolves epoch by epoch. `checkpoints` = [{record_id, step}].

    Each is resolved to the deployed LoRA of its step; checkpoints with no deployed
    LoRA are SKIPPED (reported, never a silent no-op). None resolvable → needs_setup
    True so the route answers an actionable 409 instead of launching an empty run.
    GPU serialization is the engine's own (each cell rides the serial image queue,
    which the queue leaves pending while a training/vision pass holds the GPU); the
    training→409 guard sits in the route. Stores/refreshes a CheckpointPreview per
    rendered checkpoint pointing at the reused LoraTestImage row (regeneration just
    re-points it). Returns {queued, skipped:[{record_id,step,reason}], needs_setup,
    seed}."""
    from ..models import CheckpointPreview
    fam = (family or '').strip().lower() or None
    if fam is None:
        ds = fds.get_dataset(cfg.LOCAL_USER, dataset_id)
        fam = (getattr(ds, 'train_type', None) or 'zimage').lower() if ds else 'zimage'
    # Per RUN: the map is the same dataset+family one, plus that run's own
    # step-less final deploy mapped onto its final step (cached per record so a
    # multi-checkpoint selection scans its runs once).
    by_run = {}
    resolved, skipped = [], []
    for c in (checkpoints or []):
        try:
            rid, step = int(c['record_id']), int(c['step'])
        except (KeyError, TypeError, ValueError):
            continue
        if rid not in by_run:
            by_run[rid] = _testable_for_record(dataset_id, fam, rid)
        fn = by_run[rid].get(step)
        if not fn:
            skipped.append({'record_id': rid, 'step': step, 'reason': 'not_deployed'})
            continue
        resolved.append((rid, step, fn))
    if not resolved:
        return {'queued': 0, 'skipped': skipped, 'needs_setup': True, 'seed': None}

    from . import lora_test_studio as studio
    # Pin the engine to EXACTLY these checkpoints at strength 1.0, one image each
    # (count=1). The Studio validates/preflights + enqueues; a GpuBusyError (vision
    # holding the GPU) or a StudioAssetsMissing (ComfyUI not set up) propagates and
    # the route maps it to the same structured error the Studio already returns.
    result = studio.create_run(
        user_id, dataset_id, checkpoints=[fn for _, _, fn in resolved],
        strengths=[1.0], seed=seed, prompt=prompt, family=fam, count=1,
        # The caller KNOWS which lineage checkpoint each file is — it was just
        # resolved above — so every cell records it rather than the app deriving
        # it back from the filename later.
        origins={fn: {'record_id': rid, 'step': step} for rid, step, fn in resolved})
    ids = result.get('ids') or []
    run_seed = result.get('seed', seed)
    # Single base model × single strength × count=1 → cells are 1:1 with `resolved`
    # in order; zip guards against any engine-side short count (never a wrong link).
    #
    # A NEW row per generation: previews accumulate (the unique constraint that
    # forced one row per checkpoint was lifted — see
    # services.checkpoint_preview_migration). Regenerating an epoch used to
    # re-point the single row and the earlier image became unreachable.
    for (rid, step, _fn), img_id in zip(resolved, ids):
        db.session.add(CheckpointPreview(
            record_id=rid, step=step, dataset_id=dataset_id,
            lora_test_image_id=img_id, prompt=prompt or '', seed=run_seed))
    db.session.commit()
    return {'queued': len(resolved), 'skipped': skipped, 'needs_setup': False,
            'seed': run_seed}


def _record_checkpoints_on_disk(rec) -> int:
    """How many of this run's checkpoints are still on disk RIGHT NOW — the guard
    the "remove a gone run" action checks. Mirrors the graph badge: a cloud run
    counts its staging saves (plus a harvested final LoRA), a local run counts the
    run-dir files the checkpoint scan attributes to this record. Best-effort: a
    scan we can't run reports 0 — an unprovable presence must never block removing
    a run the graph already shows as gone, and never raise (no 500)."""
    try:
        if rec.source == 'cloud':
            crun = (db.session.get(CloudTrainingRun, rec.cloud_run_id)
                    if rec.cloud_run_id else None)
            if crun is None:
                return 0
            n = _staging_save_count(crun)
            if not n and crun.checkpoint_local_path \
                    and os.path.isfile(crun.checkpoint_local_path):
                n = 1
            return n
        return len(_node_checkpoints(rec, None))
    except Exception:
        return 0


def _releasable_blob_sigs(rec) -> set:
    """Content hashes archived for `rec` that NO OTHER run references.

    `run_archive` is content-addressed and therefore shared on purpose: an
    unchanged dataset trained ten times stores its images ONCE, which is why a
    whole training history stays small. So "free this run's archived images"
    can only mean the blobs whose last referrer is this run — anything else
    would blank the image comparison of a run nobody asked to touch.

    The reference is the run snapshot (`run_snapshot.signatures`). Every path
    that cannot be accounted for cleanly returns an EMPTY set — nothing is
    deleted — rather than guessing:
      • this run has no snapshot (legacy run): its blobs are unattributable;
      • the `snapshot` column doesn't exist yet (a database whose boot migration
        hasn't run): the sweep would raise, so it is caught and yields nothing.
    Extra archived bytes are cheap; a hole in the archive is not."""
    from ..models import TrainingRunRecord
    from . import run_snapshot
    try:
        mine = run_snapshot.signatures(run_snapshot.loads(rec))
        if not mine:
            return set()
        rows = db.session.query(TrainingRunRecord.snapshot).filter(
            TrainingRunRecord.id != rec.id).all()
        for (raw,) in rows:
            mine -= run_snapshot.signatures_of_raw(raw)
            if not mine:
                break
        return mine
    except Exception:
        logger.debug('archive reference accounting failed — releasing nothing',
                     exc_info=True)
        return set()


def run_deletion_impact(record_id) -> dict | None:
    """What removing this run would actually take with it, COUNTED — the payload
    the confirmation dialog reads so a destructive action is announced before it
    happens, not discovered after.

    Every count degrades to 0 on its own rather than failing the preview: a
    fresh install with empty tables, a run that was never previewed or tested,
    an archive that doesn't exist. `None` when the run is unknown."""
    from ..models import (TrainingRunRecord, CheckpointNote, CheckpointPreview,
                          LoraTestImage, CanvasNodePosition)
    from . import run_archive
    rec = db.session.get(TrainingRunRecord, int(record_id))
    if rec is None:
        return None

    def _count(model):
        try:
            return int(model.query.filter_by(record_id=rec.id).count())
        except Exception:
            logger.debug('deletion impact count failed for %s', model, exc_info=True)
            return 0

    try:
        released = run_archive.stored_count(_releasable_blob_sigs(rec))
    except Exception:
        released = 0
    # The CASCADE half of the same preview: what a "delete everything" would take
    # that the conservative removal would not. Additive — the existing dialog
    # reads the flat keys and is untouched by it — and self-degrading to a
    # zeroed block, so a probe that cannot run never breaks the preview.
    try:
        from . import run_cascade_delete
        cascade = run_cascade_delete.cascade_impact(rec.id)
    except Exception:
        logger.debug('cascade impact preview failed', exc_info=True)
        cascade = None
    return {
        'record_id': rec.id,
        'has_saves': _record_checkpoints_on_disk(rec) > 0,
        'cascade': cascade or {
            'checkpoints': 0, 'checkpoint_bytes': 0, 'images_deleted': 0,
            'images_kept_rated': 0, 'deployed_kept': 0, 'training_active': None},
        'notes': _count(CheckpointNote),
        'previews': _count(CheckpointPreview),
        'images_unlinked': _count(LoraTestImage),
        'canvas_positions': _count(CanvasNodePosition),
        'children_detached': _count_children(rec),
        'archived_images_released': released,
    }


def _count_children(rec) -> int:
    from ..models import TrainingRunRecord
    try:
        return int(TrainingRunRecord.query
                   .filter_by(parent_record_id=rec.id).count())
    except Exception:
        return 0


def delete_run_record(record_id, cascade=False) -> str:
    """Remove a GONE run from the lineage graph, with EVERYTHING that only
    existed because of it. Five tables carry a `record_id`; leaving three of
    them behind is how a "deleted" run keeps haunting the canvas and the
    checkpoint gallery.

    What goes, and why it goes that way:
      • `TrainingRunRecord` + its `CheckpointNote`s + its `CheckpointPreview`
        links (a checkpoint may hold several previews since the uniqueness
        constraint was lifted) + its `CanvasNodePosition` (a board coordinate
        for a card that no longer exists);
      • children that resumed FROM this run are DETACHED (parent_record_id →
        NULL), staying in the graph as honest "origin unknown" roots;
      • `LoraTestImage` rows are UNLINKED (`record_id`/`step` → NULL), never
        deleted. Those are real generated pictures that also live in the Test
        Studio and the canvas gallery; removing a run is a tidying of lineage,
        not an order to destroy images the user never said to destroy. They lose
        their provenance, and the confirmation dialog says so up front;
      • archived source blobs are released ONLY when this run was their last
        referrer (`_releasable_blob_sigs`) — the store is shared between runs and
        a naive delete would blank another run's comparison.

    Guards kept: a run whose checkpoints are still on disk is REFUSED
    ('has_saves') so a recoverable run is never discarded from under the user.

    `cascade=True` is the ONE caller allowed past that guard:
    ``run_cascade_delete.delete_run_cascade`` has just moved those checkpoints to
    the trash itself, so re-asking "are they on disk?" would either refuse a
    deletion whose files are already gone or race a slow filesystem. It is a
    keyword with a False default so every existing caller keeps the conservative
    behaviour byte for byte — the cascade is an explicitly requested mode, never
    a new default that starts destroying files under code that never asked.

    Returns 'not_found' | 'has_saves' | 'deleted' | 'conflict'. The FK children
    (no relationship cascade in this schema) are deleted and FLUSHED before the
    parent row so SQLite never raises the repo's "delete 500" IntegrityError; a
    stray one is caught and reported as 'conflict', never a 500. Blobs are
    touched only AFTER the commit succeeds — a filesystem hiccup must never roll
    back a database deletion, and vice versa."""
    from ..models import (TrainingRunRecord, CheckpointNote, CheckpointPreview,
                          LoraTestImage, CanvasNodePosition)
    from . import run_archive
    from sqlalchemy.exc import IntegrityError
    rec = db.session.get(TrainingRunRecord, int(record_id))
    if rec is None:
        return 'not_found'
    if not cascade and _record_checkpoints_on_disk(rec) > 0:
        return 'has_saves'
    # Computed BEFORE the row is gone — the snapshot that names the blobs lives
    # on the record itself.
    releasable = _releasable_blob_sigs(rec)
    try:
        # Detach any run that resumed from this one BEFORE deleting it: the child
        # stays displayed (as a root), the parent edge just disappears.
        (TrainingRunRecord.query
         .filter_by(parent_record_id=rec.id)
         .update({'parent_record_id': None}, synchronize_session=False))
        # Generated images survive their run: only the provenance link is cut.
        (LoraTestImage.query
         .filter_by(record_id=rec.id)
         .update({'record_id': None, 'step': None}, synchronize_session=False))
        # Delete FK children first and flush, so deleting the parent row can't hit
        # an IntegrityError (the "delete 500" trap — no cascade on these tables).
        CheckpointNote.query.filter_by(record_id=rec.id).delete(
            synchronize_session=False)
        CheckpointPreview.query.filter_by(record_id=rec.id).delete(
            synchronize_session=False)
        CanvasNodePosition.query.filter_by(record_id=rec.id).delete(
            synchronize_session=False)
        db.session.flush()
        db.session.delete(rec)
        db.session.commit()
    except IntegrityError:
        db.session.rollback()
        return 'conflict'
    try:
        run_archive.release(releasable)
    except Exception:
        logger.debug('archived blobs could not be released', exc_info=True)
    return 'deleted'


def _lineage_node(rec, crun, requested_id, failed_local_id):
    """One genealogy-tree node from a provenance record, enriched with what the
    card badge shows: family/variant/base/version/date, run status, and whether
    its LoRA/checkpoints are still ON DISK vs gone (superseded aside or deleted).
    Each node also carries its own `checkpoints` (the ◉ Graph draws them as pills
    under the run and anchors a continuation's edge on the exact one it resumed).
    Checkpoint presence is best-effort — a disk scan that fails degrades to
    None (the UI shows nothing) rather than a wrong "available" claim."""
    node = {
        'record_id': rec.id,
        'parent_record_id': rec.parent_record_id,
        'resumed_from': rec.resumed_from,
        'source': 'cloud' if rec.source == 'cloud' else 'local',
        'dataset_id': rec.dataset_id,
        'dataset_name': _dataset_name(rec.dataset_id),
        'train_type': rec.family,
        'variant': rec.variant,
        'base_model': rec.base_model or '',
        'version': rec.version,
        'steps': rec.steps,
        'config': _rec_config(rec),
        'note': rec.note or '',
        'has_note': bool((rec.note or '').strip()),
        'created_at': rec.created_at.isoformat() if rec.created_at else None,
        'is_current': rec.id == requested_id,
        # A record with a resume step but no resolvable parent (legacy: the edge
        # was never persisted) is an honest ROOT with a discreet "origin unknown".
        'origin_unknown': bool(rec.resumed_from and not rec.parent_record_id),
    }
    if crun is not None:
        node['run_id'] = crun.id
        node['status'] = crun.status
        node['checkpoint_ready'] = bool(
            crun.checkpoint_local_path and os.path.isfile(crun.checkpoint_local_path))
        node['checkpoints'] = _node_checkpoints(rec, crun)
        node['saves'] = _staging_save_count(crun)
    else:
        node['status'] = ('error' if (rec.source == 'local'
                                       and rec.id == failed_local_id) else None)
        # Local checkpoints still on disk that list_checkpoints attributes to
        # THIS record (record_for_mtime). Superseded/deleted saves simply don't
        # appear — honest "what's recoverable now", never invented.
        try:
            cks = _node_checkpoints(rec, None)
            node['checkpoints'] = cks
            node['saves'] = len(cks)
            node['checkpoint_ready'] = len(cks) > 0
        except Exception:
            node['checkpoints'] = []
            node['saves'] = None
            node['checkpoint_ready'] = None
    _cnotes = checkpoint_notes_for(rec.id)
    _cprev = checkpoint_previews_for(rec.id)
    # Deployment (testable + the deployed copy's own name) comes from the SHARED
    # annotator, so the graph pills and the Checkpoints panel rows answer "is this
    # deployed, and which ComfyUI file is it?" with the same join. Scoped to THIS
    # run so its step-less final deploy (`..._rc90_v2`, no step in the name) joins
    # its own final pill instead of going unmatched.
    annotate_deployed_checkpoints(rec.dataset_id, rec.family,
                                  node.get('checkpoints') or [],
                                  run_tag=_deployed_run_tag(rec))
    for _ck in (node.get('checkpoints') or []):
        _step = _ck.get('step')
        _ck['note'] = _cnotes.get(_step, '')
        # `preview_*` render the inline thumbnail (or its pending/failed state);
        # `preview_count` is the SIZE of the checkpoint's gallery — every image it
        # ever produced, from any surface — which the pill shows as a × N badge.
        _pv = _cprev.get(_step)
        if _pv:
            _ck['preview_url'] = _pv.get('url')
            _ck['preview_status'] = _pv.get('status')
            _ck['preview_count'] = _pv.get('count') or 0
    return node


def annotate_deployed_checkpoints(dataset_id, family, checkpoints,
                                  run_tag=None) -> list:
    """Stamp `testable` and, when deployed, `deployed_filename` onto a flat list
    of a run's saves — IN PLACE, returning the same list.

    This is THE join between "a save on disk" and "its copy in ComfyUI", and it
    has exactly one implementation on purpose: the ◉ Graph pills and the
    Checkpoints & LoRAs rows must never disagree about which checkpoints are
    deployed, nor about which file an undeploy would remove. `testable` decides
    "✓ Deployed vs 📦 Import"; `deployed_filename` is the ONLY handle the UI has
    on the ComfyUI copy (without it the delete route answers "unknown checkpoint"
    and the action is withheld) — it is resolved to the form that route accepts.

    `run_tag` ((source, run_id), see _deployed_run_tag) additionally attaches a
    run's STEP-LESS final deploy to its final save. Best-effort throughout: an
    unreadable ComfyUI pool leaves every row "not deployed" rather than claiming
    a deployment that isn't there."""
    cks = list(checkpoints or [])
    testable = _testable_by_step(dataset_id, family, run_tag=run_tag,
                                 final_step=_final_step_of(cks))
    names = _deletable_deploy_names(dataset_id, family) if testable else {}
    for ck in cks:
        step = ck.get('step')
        ck['testable'] = step in testable
        dep = testable.get(step)
        if dep:
            ck['deployed_filename'] = names.get(
                os.path.basename(str(dep).replace('\\', '/')).lower())
    return cks


def annotate_deployed_by_run(dataset_id, family, checkpoints) -> list:
    """`annotate_deployed_checkpoints` for a MIXED list whose rows name their own
    source run (the Checkpoints panel's local list: several runs' saves in one
    flat list). Rows are grouped by (run_source, run_id) so each group is joined
    with ITS run tag — a step-less final save then attaches to the run that
    produced it, never to a neighbour. Rows with no recorded run (pre-registry
    files) are joined untagged, which still matches every step-named deploy."""
    groups = {}
    for ck in (checkpoints or []):
        rid = ck.get('run_id')
        src = ck.get('run_source')
        key = (src, rid) if rid and src else (None, None)
        groups.setdefault(key, []).append(ck)
    for (src, rid), rows in groups.items():
        annotate_deployed_checkpoints(dataset_id, family, rows,
                                      run_tag=(src, rid) if rid else None)
    return list(checkpoints or [])


def run_lineage(record_id) -> dict:
    """The genealogy tree for the lineage that record_id belongs to: every
    launch (local AND cloud) linked by continuations, as nodes + parent→child
    edges. `single` is True for a lone run with no parent and no children (the
    UI then offers no tree). Superseded branch: an edge whose child resumed
    BELOW where its parent ended means the parent has saves set aside — flagged
    on the edge (superseded) and on the parent node (has_superseded_tail)."""
    from . import checkpoint_registry as reg
    from ..models import TrainingRunRecord
    records = reg.resolve_lineage(record_id)
    if not records:
        return {'nodes': [], 'edges': [], 'root_id': None,
                'current_id': None, 'single': True}
    requested_id = int(record_id)
    cloud_ids = {r.cloud_run_id for r in records if r.cloud_run_id}
    cloud_by_id = ({r.id: r for r in CloudTrainingRun.query
                    .filter(CloudTrainingRun.id.in_(cloud_ids)).all()}
                   if cloud_ids else {})
    failed_local_id = (lt.failed_local_run() or (None, None))[0]
    nodes = [_lineage_node(rec, cloud_by_id.get(rec.cloud_run_id),
                           requested_id, failed_local_id)
             for rec in records]
    steps_by_id = {r.id: (r.steps or 0) for r in records}
    edges, superseded_parents = [], set()
    for rec in records:
        pid = rec.parent_record_id
        if pid and pid in steps_by_id:
            superseded = (rec.resumed_from is not None
                          and rec.resumed_from < steps_by_id[pid])
            if superseded:
                superseded_parents.add(pid)
            edges.append({'parent': pid, 'child': rec.id,
                          'resumed_from': rec.resumed_from,
                          'superseded': superseded})
    for node in nodes:
        node['has_superseded_tail'] = node['record_id'] in superseded_parents
    return {'root_id': records[0].id, 'current_id': requested_id,
            'nodes': nodes, 'edges': edges, 'single': len(nodes) < 2}


def _lineage_edges(records):
    """parent→child edges over a SET of records (the genealogy the ◉ Graph draws),
    with the superseded flag (a child resumed BELOW where its parent ended) — the
    same rule run_lineage uses, factored so a dataset-wide forest reuses it."""
    steps_by_id = {r.id: (r.steps or 0) for r in records}
    ids = set(steps_by_id)
    edges, superseded_parents = [], set()
    for rec in records:
        pid = rec.parent_record_id
        if pid and pid in ids:
            superseded = (rec.resumed_from is not None
                          and rec.resumed_from < steps_by_id[pid])
            if superseded:
                superseded_parents.add(pid)
            edges.append({'parent': pid, 'child': rec.id,
                          'resumed_from': rec.resumed_from,
                          'superseded': superseded})
    return edges, superseded_parents


def dataset_lineage(dataset_id, train_type=None, variant=None) -> dict:
    """Every run this dataset produced, as ONE genealogy forest for the ◉ Graph
    the Checkpoints & LoRAs manager opens — not a single record's lineage but all
    of them (several independent trees stack; the graph layout already handles
    multiple roots). Optionally scoped to the family/variant the panel is showing,
    so it matches the checkpoints listed there. Nodes carry their checkpoints
    exactly like run_lineage; there is no single 'current' run here (root_id /
    current_id are None). Empty dataset → an empty, safe shape."""
    from ..models import TrainingRunRecord
    fam = fds.normalize_train_type(train_type) if train_type else None
    q = TrainingRunRecord.query.filter_by(dataset_id=dataset_id)
    if fam:
        q = q.filter_by(family=fam)
    if variant:
        q = q.filter_by(variant=str(variant).strip().lower())
    records = q.order_by(TrainingRunRecord.id.asc()).all()
    if not records:
        return {'nodes': [], 'edges': [], 'root_id': None,
                'current_id': None, 'single': True}
    cloud_ids = {r.cloud_run_id for r in records if r.cloud_run_id}
    cloud_by_id = ({r.id: r for r in CloudTrainingRun.query
                    .filter(CloudTrainingRun.id.in_(cloud_ids)).all()}
                   if cloud_ids else {})
    failed_local_id = (lt.failed_local_run() or (None, None))[0]
    nodes = [_lineage_node(rec, cloud_by_id.get(rec.cloud_run_id), None,
                           failed_local_id) for rec in records]
    edges, superseded_parents = _lineage_edges(records)
    for node in nodes:
        node['has_superseded_tail'] = node['record_id'] in superseded_parents
    return {'root_id': None, 'current_id': None,
            'nodes': nodes, 'edges': edges, 'single': len(nodes) < 2}


def canvas_dataset_index(user_id) -> dict:
    """The LoRA Canvas' INDEX: every dataset of `user_id` that produced at least
    one training run, with its run count and the families it covers.

    Deliberately cheap — two grouped queries, no checkpoints, no disk. The canvas
    draws its dataset filter from this and then pulls each shown dataset's
    genealogy through the existing per-dataset lineage endpoint. Assembling the
    whole forest in one response would have to scan every run's saves on disk
    before ANYTHING could appear on screen, and a library of thirty datasets
    would stare at a spinner for it. Datasets with no run are omitted: there is
    nothing to draw for them, and offering them in the filter would only be a
    list of dead ends.

    Ordered newest-run-first, so the board opens on what was trained recently."""
    from sqlalchemy import func
    from ..models import TrainingRunRecord
    from . import lora_test_studio as studio
    datasets = {d.id: d for d in fds.list_datasets(user_id)}
    if not datasets:
        return {'datasets': []}
    ids = list(datasets)
    rows = (db.session.query(TrainingRunRecord.dataset_id,
                             func.count(TrainingRunRecord.id),
                             func.max(TrainingRunRecord.created_at))
            .filter(TrainingRunRecord.dataset_id.in_(ids))
            .group_by(TrainingRunRecord.dataset_id).all())
    fams = {}
    for ds_id, fam in (db.session.query(TrainingRunRecord.dataset_id,
                                        TrainingRunRecord.family)
                       .filter(TrainingRunRecord.dataset_id.in_(ids))
                       .distinct().all()):
        if fam:
            fams.setdefault(ds_id, set()).add(fam)
    out = []
    for ds_id, runs, last_at in rows:
        ds = datasets.get(ds_id)
        if ds is None:
            continue
        out.append({
            'id': ds_id,
            'name': ds.name,
            'runs': int(runs or 0),
            'families': sorted(fams.get(ds_id) or ()),
            'last_run_at': last_at.isoformat() if last_at else None,
            # The ★ pinned LoRA(s), one per family. Read off the dataset row we
            # ALREADY hold — no extra query, no disk. Without it a canvas delete
            # of the pinned checkpoint was confirmed with the plain wording, and
            # the ⚠ "this is your saved winning combo" line never appeared:
            # same route, same trash, but the user was not told what they were
            # about to break.
            'best_settings_loras': studio.best_settings_lora_filenames(ds),
        })
    out.sort(key=lambda d: (d['last_run_at'] or '', d['id']), reverse=True)
    return {'datasets': out}


# --- ◉ LoRA Canvas: remembered card positions -------------------------------
#
# The canvas draws its trees with the automatic layout and lets the user drag a
# card off it. These three functions are the whole persistence story: read the
# board's overrides, upsert some, drop a lane's. Everything about WHICH cards get
# a row and where they land is decided client-side by the pure placement layer
# (frontend/src/utils/canvasPlacement.js) — the server stores coordinates and
# asks no questions, so the geometry stays testable without a browser.
#
# Positions are a display preference. A failed write must never interrupt what
# the user is doing (design: "nothing about the canvas may block the canvas"),
# which is why these are plain, boring upserts with no side effects.

def canvas_positions(user_id, dataset_ids=None) -> dict:
    """Every remembered card position of `user_id`, grouped by dataset id.

    One request for the whole board on purpose: the canvas opens on N lanes and
    N round-trips for a handful of tiny rows would be slower than the genealogy
    fetches they have to be ready before. `dataset_ids` narrows it when the
    caller already knows the lanes it wants."""
    from ..models import CanvasNodePosition
    owned = {d.id for d in fds.list_datasets(user_id)}
    if dataset_ids is not None:
        owned &= {int(i) for i in dataset_ids}
    if not owned:
        return {'positions': {}}
    rows = (CanvasNodePosition.query
            .filter(CanvasNodePosition.dataset_id.in_(list(owned))).all())
    out = {}
    for r in rows:
        out.setdefault(str(r.dataset_id), []).append(
            {'record_id': r.record_id, 'x': float(r.x), 'y': float(r.y)})
    for lane in out.values():
        lane.sort(key=lambda p: p['record_id'])
    return {'positions': out}


def save_canvas_positions(user_id, dataset_id, positions) -> dict:
    """Upsert card positions for one lane. Returns how many rows the lane holds.

    Idempotent by (dataset_id, record_id) — the canvas re-sends a position on
    every drop and re-pins the same coordinates whenever a lane gains a run, so
    a second identical write must be a no-op rather than a duplicate row.
    Non-finite coordinates are rejected outright: one NaN stored here would make
    a card unreachable on every future load, and there is no UI to fix it."""
    from ..models import CanvasNodePosition
    if not fds.get_dataset(user_id, dataset_id):
        raise LookupError('dataset not found')
    wanted = {}
    for p in (positions or []):
        try:
            rid = int(p['record_id'])
            x, y = float(p['x']), float(p['y'])
        except (KeyError, TypeError, ValueError):
            continue
        if not (x == x and y == y and abs(x) != float('inf') and abs(y) != float('inf')):
            continue
        wanted[rid] = (x, y)
    if wanted:
        existing = {r.record_id: r for r in CanvasNodePosition.query.filter(
            CanvasNodePosition.dataset_id == dataset_id,
            CanvasNodePosition.record_id.in_(list(wanted))).all()}
        for rid, (x, y) in wanted.items():
            row = existing.get(rid)
            if row is None:
                db.session.add(CanvasNodePosition(
                    dataset_id=dataset_id, record_id=rid, x=x, y=y))
            else:
                row.x, row.y = x, y
        db.session.commit()
    return {'saved': len(wanted),
            'total': CanvasNodePosition.query.filter_by(dataset_id=dataset_id).count()}


def clear_canvas_positions(user_id, dataset_id) -> dict:
    """✦ Tidy up for one lane: drop every remembered position so the automatic
    tree takes over again. The escape hatch — an arrangement tangled over twenty
    runs has to have a way back that is not "edit the database"."""
    from ..models import CanvasNodePosition
    if not fds.get_dataset(user_id, dataset_id):
        raise LookupError('dataset not found')
    removed = CanvasNodePosition.query.filter_by(
        dataset_id=dataset_id).delete(synchronize_session=False)
    db.session.commit()
    return {'cleared': int(removed or 0)}


# 🖼 Bounds for a pinned image node, in the board's WORLD units (a run card is
# CARD_W = 264 wide, for scale). The floor keeps a node grabbable at any zoom;
# the ceiling is the one that matters — a node resized to 8 000 px would blow
# up its lane's extent, and ✦ Fit would then collapse the whole board to a scale
# where nothing else is readable. Enforced here as well as in the browser: the
# clamp protects the NEXT load, not just the gesture.
CANVAS_IMAGE_MIN = 96.0
CANVAS_IMAGE_MAX = 1400.0


def _clamp_image_box(x, y, w, h):
    """Lane-local geometry, clamped. Returns None for anything unusable —
    a NaN stored here would make a node unreachable on every future load and
    there is no UI to fix that."""
    try:
        x, y, w, h = float(x), float(y), float(w), float(h)
    except (TypeError, ValueError):
        return None
    for v in (x, y, w, h):
        if v != v or abs(v) == float('inf'):
            return None
    return (max(0.0, x), max(0.0, y),
            min(CANVAS_IMAGE_MAX, max(CANVAS_IMAGE_MIN, w)),
            min(CANVAS_IMAGE_MAX, max(CANVAS_IMAGE_MIN, h)))


def canvas_image_nodes(user_id, dataset_ids=None) -> dict:
    """🖼 Every image pinned on the board, grouped by dataset id — geometry AND
    the image row itself, so a lane can draw its pinned pictures without a
    second round-trip per node.

    Rows whose image no longer exists are DELETED here rather than returned.
    That is the answer to the ghost node: an image deleted from a gallery (or
    with its whole dataset) leaves a row pointing at nothing, and a node that
    renders a broken picture forever is a bug that only shows up weeks later.
    The board simply loses it, silently, which is what "the picture is gone"
    should look like.

    ``visible: false`` rows ARE returned: that is the closed-but-remembered
    state, and the panel needs it to re-open an image exactly where it was."""
    from ..models import CanvasImageNode, LoraTestImage
    owned = {d.id for d in fds.list_datasets(user_id)}
    if dataset_ids is not None:
        owned &= {int(i) for i in dataset_ids}
    if not owned:
        return {'nodes': {}, 'pruned': 0}
    rows = (CanvasImageNode.query
            .filter(CanvasImageNode.dataset_id.in_(list(owned))).all())
    if not rows:
        return {'nodes': {}, 'pruned': 0}
    imgs = {i.id: i for i in LoraTestImage.query.filter(
        LoraTestImage.id.in_([r.image_id for r in rows]),
        LoraTestImage.status == 'done',
        LoraTestImage.filename.isnot(None)).all()}
    out, pruned = {}, 0
    for r in rows:
        img = imgs.get(r.image_id)
        if img is None:
            db.session.delete(r)
            pruned += 1
            continue
        out.setdefault(str(r.dataset_id), []).append({
            'image_id': r.image_id,
            'x': float(r.x), 'y': float(r.y),
            'w': float(r.w), 'h': float(r.h),
            'visible': bool(r.visible),
            'image': _gallery_image(img),
        })
    if pruned:
        db.session.commit()
    for lane in out.values():
        lane.sort(key=lambda n: n['image_id'])
    return {'nodes': out, 'pruned': pruned}


def save_canvas_image_nodes(user_id, dataset_id, nodes) -> dict:
    """Upsert pinned-image geometry for one lane.

    Body rows are {image_id, x, y, w, h, visible}. Idempotent by
    (dataset_id, image_id): a drag re-sends the node on every drop, and closing
    one re-sends it with ``visible: false`` — the row and its geometry survive,
    which is the entire point (re-opening restores where and how big it was).

    An image that does not belong to this dataset is refused, so a pinned node
    can never smuggle another dataset's render into this lane."""
    from ..models import CanvasImageNode, LoraTestImage
    if not fds.get_dataset(user_id, dataset_id):
        raise LookupError('dataset not found')
    wanted = {}
    for n in (nodes or []):
        try:
            iid = int(n['image_id'])
        except (KeyError, TypeError, ValueError):
            continue
        box = _clamp_image_box(n.get('x'), n.get('y'), n.get('w'), n.get('h'))
        if box is None:
            continue
        wanted[iid] = (box, bool(n.get('visible', True)))
    if not wanted:
        return {'saved': 0,
                'total': CanvasImageNode.query.filter_by(dataset_id=dataset_id).count()}
    legit = {i.id for i in LoraTestImage.query.filter(
        LoraTestImage.id.in_(list(wanted)),
        LoraTestImage.dataset_id == dataset_id).all()}
    existing = {r.image_id: r for r in CanvasImageNode.query.filter(
        CanvasImageNode.dataset_id == dataset_id,
        CanvasImageNode.image_id.in_(list(wanted))).all()}
    saved = 0
    for iid, ((x, y, w, h), visible) in wanted.items():
        if iid not in legit:
            continue
        row = existing.get(iid)
        if row is None:
            db.session.add(CanvasImageNode(
                dataset_id=dataset_id, image_id=iid, x=x, y=y, w=w, h=h,
                visible=visible))
        else:
            row.x, row.y, row.w, row.h, row.visible = x, y, w, h, visible
        saved += 1
    db.session.commit()
    return {'saved': saved,
            'total': CanvasImageNode.query.filter_by(dataset_id=dataset_id).count()}


def clear_canvas_image_nodes(user_id, dataset_id) -> dict:
    """Forget every pinned image of one lane — geometry included.

    NOT what ✦ Tidy up calls. Tidy up hands a lane back to the automatic tree,
    and there is no automatic position for a pinned image to fall back to, so
    "tidying" one could only mean throwing it away. This exists as the deliberate
    escape hatch, and nothing invokes it by accident."""
    from ..models import CanvasImageNode
    if not fds.get_dataset(user_id, dataset_id):
        raise LookupError('dataset not found')
    removed = CanvasImageNode.query.filter_by(
        dataset_id=dataset_id).delete(synchronize_session=False)
    db.session.commit()
    return {'cleared': int(removed or 0)}


def gpu_tiers(user_id, dataset_id, train_type=None, steps=None,
              variant=None) -> dict:
    """Live vast.ai offers for THIS dataset+family, grouped by GPU class
    (cheapest offer per class), ranked slowest -> fastest, each annotated with
    an approximate training time and total run cost. Read-only: rents nothing.
    The launch then re-searches and rents the cheapest live offer of the chosen
    class. Raises the same guards as launch (no key / dataset / SDXL)."""
    if not cfg.secret('VAST_API_KEY'):
        raise RuntimeError('vast.ai API key is not configured — add it in Settings')
    ds = fds.get_dataset(user_id, dataset_id)
    if not ds:
        raise ValueError('dataset not found')
    fam = fds.normalize_train_type(train_type or getattr(ds, 'train_type', None))
    # Slider mode rides the same offers/pods as its family (see
    # launch_cloud_training) — no separate refusal here.
    if fam == 'sdxl':
        raise ValueError('SDXL training needs a local base checkpoint — '
                         'cloud training supports Z-Image, Krea and FLUX.2 Klein')
    # flux2klein passe (cf. launch_cloud_training) — seul flux reste local-only.
    if fam == 'flux':
        raise ValueError('FLUX.1 training is local-only for now — '
                         'cloud training supports Z-Image, Krea and FLUX.2 Klein')
    # Anima is LOCAL-ONLY for this wave: a pod would need ai-toolkit with the
    # 'anima' arch (PR #860, 2026-07-15) + a recent diffusers, which current pod
    # images predate — renting one would burn a GPU on an unknown arch. Refuse
    # BEFORE any reservation. Lift once the pod image is verified.
    if fam == 'anima':
        raise ValueError('Anima cloud training is coming once the pod image is '
                         'verified — train it locally for now')
    selected_variant = str(
        variant or getattr(ds, 'train_variant', None)
        or lt._default_variant_for(fam)).strip().lower()
    if selected_variant not in lt._valid_variants_for(fam):
        selected_variant = lt._default_variant_for(fam)
    n_steps = (int(steps) if steps else lt.default_steps(
        ds, train_type=fam, variant=selected_variant))
    c = cfg.get('cloud') or {}
    min_vram = (c.get('min_vram_gb') or {}).get(fam, 24)
    price_cap = c.get('max_price_per_hour', 0.80)
    overhead_min = float(c.get('pod_overhead_minutes') or 0)
    # A wider scan than the launch default so several GPU classes surface (the
    # user is choosing between them, not taking the single cheapest). Same
    # quality filters as the launch so the shown tiers match what gets rented.
    offers = _filter_offers(vast_client.search_offers(
        min_vram_gb=min_vram, max_dph=price_cap,
        limit=int(c.get('offer_scan_limit') or 100),
        min_inet_down_mbps=int(c.get('min_inet_down_mbps') or 0),
        min_reliability=float(c.get('min_reliability') or 0.98),
        min_disk_bw_mbps=int(c.get('min_disk_bw_mbps') or 0),
        verified_only=bool(c.get('verified_only', True)),
        secure_cloud_only=bool(c.get('secure_cloud_only', False))))
    cheapest_by_gpu = {}
    for o in offers:
        name = o.get('gpu_name') or 'GPU'
        cur = cheapest_by_gpu.get(name)
        dph = o.get('dph_total')
        if cur is None or (dph is not None and (cur.get('dph_total') is None
                           or dph < cur['dph_total'])):
            cheapest_by_gpu[name] = o
    max_runtime = int(c.get('max_runtime_minutes') or 480)
    tiers = []
    for name, o in cheapest_by_gpu.items():
        dph = o.get('dph_total')
        est_min = gpu_speed.estimate_minutes(name, fam, n_steps)
        # Cost bills the whole pod life: training + boot/download/quantize.
        est_cost = (round(dph * (est_min + overhead_min) / 60.0, 2)
                    if dph is not None else None)
        tiers.append({
            'gpu_name': name, 'offer_id': o.get('offer_id'),
            'dph_total': round(dph, 4) if dph is not None else None,
            'gpu_ram_gb': o.get('gpu_ram_gb'),
            'speed': round(gpu_speed.speed_factor(name), 2),
            'est_minutes': int(round(est_min)), 'est_cost': est_cost,
            # A tier slower than the runtime cap would be KILLED mid-training
            # (checkpoint rescued, but steps lost) — warn at pick time.
            'exceeds_cap': (est_min + overhead_min) > max_runtime,
        })
    # slowest -> fastest (matches the launch dialog); ties broken by price.
    tiers.sort(key=lambda t: (t['speed'], t['dph_total']
                              if t['dph_total'] is not None else 9e9))
    return {'tiers': tiers, 'steps': n_steps, 'family': fam,
            'variant': selected_variant,
            'max_price_per_hour': price_cap,
            'max_runtime_minutes': max_runtime}


def cloud_checkpoint_groups(dataset_id, train_type=None, variant=None) -> list:
    """Locally-synced cloud checkpoints GROUPED by their source run (newest run
    first, step-sorted within a run). Each group carries the run's identity and
    outcome — id / status / GPU / cost / timing, the SAME facts the Runs hub
    shows — so the Checkpoints panel can label WHICH run produced which epochs
    and deep-link back to its row, instead of listing several indistinguishable
    step-500→final sets. Runs whose saves were all hand-deleted are omitted."""
    fam = fds.normalize_train_type(train_type) if train_type else None
    wanted_variant = str(variant).strip().lower() if variant else None
    groups = []
    for run in (CloudTrainingRun.query.filter_by(dataset_id=dataset_id)
                .order_by(CloudTrainingRun.id.desc()).all()):
        if fam and (_run_family(run) or fam) != fam:
            continue
        if wanted_variant and (
                str(_run_param(run, 'variant') or wanted_variant).lower()
                != wanted_variant):
            continue
        if not run.staging_dir or not os.path.isdir(run.staging_dir):
            continue
        run_variant = _run_param(run, 'variant')
        entries = []
        for name in os.listdir(run.staging_dir):
            if not name.lower().endswith('.safetensors'):
                continue
            m = re.search(r'_(\d{6,})\.safetensors$', name)
            step = int(m.group(1)) if m else int(_run_param(run, 'steps') or 0)
            entries.append({'filename': name, 'step': step, 'cloud': True,
                            'run_id': run.id, 'version': _run_param(run, 'version'),
                            'variant': run_variant,
                            'final': bool(not m and run.status == 'done'),
                            'active': run.status in ACTIVE_STATES,
                            'trained_at': run.created_at.isoformat()
                                          if run.created_at else None})
        if not entries:
            continue
        entries.sort(key=lambda e: (e['step'], e['final']))
        groups.append({
            'run_id': run.id, 'source': 'cloud', 'status': run.status,
            'active': run.status in ACTIVE_STATES, 'gpu': run.gpu_name,
            'price_per_hour': run.price_per_hour,
            'cost_estimate': _cost_estimate(run),
            'version': _run_param(run, 'version'), 'variant': run_variant,
            'train_type': _run_family(run),
            'created_at': run.created_at.isoformat() if run.created_at else None,
            'finished_at': run.finished_at.isoformat() if run.finished_at else None,
            'checkpoints': entries,
        })
    return groups


def cloud_checkpoints(dataset_id, train_type=None, variant=None) -> list:
    """Flat view of cloud_checkpoint_groups — every synced save of this dataset
    (+family/variant filters), newest run first, step-sorted within a run. Kept
    for callers that reason on individual saves (import / delete / continue);
    the panel groups them per run via cloud_checkpoint_groups."""
    out = []
    for g in cloud_checkpoint_groups(dataset_id, train_type, variant):
        out.extend(g['checkpoints'])
    return out


def delete_cloud_checkpoint(dataset_id, run_id, filename) -> str:
    """Move a cloud run's synced checkpoint to the trash. The run must belong
    to the dataset and be TERMINAL (deleting an active run's save is pointless
    — the sync re-downloads it). Clears checkpoint_local_path when it pointed
    at the trashed file."""
    run = CloudTrainingRun.query.get(int(run_id))
    if not run or run.dataset_id != int(dataset_id) or not run.staging_dir:
        raise ValueError('unknown cloud run')
    if run.status in ACTIVE_STATES:
        raise ValueError('this cloud run is still active — its save would just '
                         'be re-synced; stop the run first')
    allowed = {f for f in os.listdir(run.staging_dir)
               if f.lower().endswith('.safetensors')}
    if filename not in allowed:
        raise ValueError('unknown checkpoint')
    from . import trash
    trash.send_to_trash(os.path.join(run.staging_dir, filename),
                        context=f'cloudckpt_run{run.id}')
    if run.checkpoint_local_path \
            and os.path.basename(run.checkpoint_local_path) == filename:
        _set(run, checkpoint_local_path=None)
    return filename


# ── Staging cleanup (global 🧹 and per-run 🧹) ────────────────────────────────
# Both entry points share ONE sparing rule and ONE trashing step, so a run that
# the global purge spares can never be trashed by the per-run button (and back).

def staging_spare_reason(run) -> str | None:
    """Why this run's staging must NOT be trashed, or None when it is fair game.
    The single source of truth for both 🧹 buttons and for the per-run button's
    disabled state — duplicating it is how the two drift apart."""
    if run.status in ACTIVE_STATES:
        return 'this run is still active — its staging is being written to'
    if run.status == 'error_pod_kept':
        return ('its pod was kept for manual recovery — clean it up after you '
                'have retrieved what you need')
    return None


def _trash_staging(run) -> int:
    """Move ONE run's staging dir to the trash; returns the bytes it held (0 when
    there was nothing on disk). Callers own the sparing check."""
    from . import trash
    sd = run.staging_dir
    if not sd or not os.path.isdir(sd):
        return 0
    size = lt._dir_size(sd)
    trash.send_to_trash(sd, context=f'staging_run{run.id}')
    _staging_size_cache.pop(run.id, None)
    if run.checkpoint_local_path:
        _set(run, checkpoint_local_path=None)
    return size


# run_id -> (expires_at, bytes). A staging dir is a dataset copy + samples +
# checkpoints — thousands of files per run, tens of thousands across a history.
# Walking them belongs to an EXPLICIT request, never to the hub's 5 s poll, and a
# short TTL keeps a re-open (or a second tab) from re-walking the same disk.
_staging_size_cache = {}
_STAGING_SIZE_TTL = 60.0


def staging_sizes(run_ids=None) -> dict:
    """{run_id: bytes on disk} for the runs whose staging dir still exists —
    what the per-run 🧹 needs to name the weight it is about to move. Runs with
    no staging (never launched, already purged, hand-deleted) are simply absent,
    which the UI reads as "nothing to clean here". Best-effort: a directory that
    cannot be walked is skipped rather than failing the whole request."""
    now = time.time()
    q = CloudTrainingRun.query
    if run_ids is not None:
        ids = [int(i) for i in run_ids]
        if not ids:
            return {}
        q = q.filter(CloudTrainingRun.id.in_(ids))
    out = {}
    for run in q.all():
        cached = _staging_size_cache.get(run.id)
        if cached and cached[0] > now:
            if cached[1]:
                out[run.id] = cached[1]
            continue
        sd = run.staging_dir
        size = 0
        if sd and os.path.isdir(sd):
            try:
                size = lt._dir_size(sd)
            except OSError as e:
                logger.warning('staging size: could not walk %s: %s', sd, e)
                continue
        _staging_size_cache[run.id] = (now + _STAGING_SIZE_TTL, size)
        if size:
            out[run.id] = size
    return out


def purge_run_staging(run_id) -> dict:
    """Per-run 🧹: move THIS run's staging dir to the trash. Same sparing rule as
    the global purge (staging_spare_reason), so the two can't disagree; the DB row
    stays (history). Raises ValueError on an unknown or spared run — the caller
    turns it into a 400 with the reason, instead of a silent no-op."""
    run = CloudTrainingRun.query.get(int(run_id))
    if not run:
        raise ValueError('unknown cloud run')
    reason = staging_spare_reason(run)
    if reason:
        raise ValueError(f'this run\'s staging is spared: {reason}')
    if not run.staging_dir or not os.path.isdir(run.staging_dir):
        return {'purged': False, 'freed_bytes': 0, 'already_clean': True}
    try:
        freed = _trash_staging(run)
    except OSError as e:
        logger.warning('purge run %s: could not trash %s: %s',
                       run.id, run.staging_dir, e)
        raise RuntimeError(f'could not move this run\'s staging to the trash: {e}')
    return {'purged': True, 'freed_bytes': freed, 'already_clean': False}


def purge_finished_runs() -> dict:
    """Hub 'Clean finished runs': move the staging dirs of TERMINAL runs to the
    trash — dataset copies, samples and checkpoint duplicates of results that
    are already imported/mirrored. Active runs and error_pod_kept (manual
    recovery may still be under way) are spared. DB rows stay (history).

    `already_clean` tells "there was nothing to purge" apart from "0 purged
    because every attempt failed" — the caller shows two different messages."""
    purged = 0
    freed = 0
    candidates = 0
    for run in CloudTrainingRun.query.all():
        if staging_spare_reason(run):
            continue
        if not run.staging_dir or not os.path.isdir(run.staging_dir):
            continue
        candidates += 1
        try:
            freed += _trash_staging(run)
            purged += 1
        except OSError as e:
            logger.warning('purge: could not trash %s: %s', run.staging_dir, e)
    return {'purged_runs': purged, 'freed_bytes': freed,
            'already_clean': candidates == 0}


def cloud_progress(user_id, dataset_id, train_type=None) -> dict:
    """Same shape as lt.training_progress + cloud phase/cost fields, built
    from the staging mirror (log + samples) written by the monitor. With
    train_type, reads THAT family's newest run (several families may train
    the same dataset in parallel)."""
    run = latest_run_for(dataset_id, train_type)
    empty = {'step': None, 'total': None, 'loss': None, 'speed': None,
             'eta': None, 'loss_curve': []}
    if not run:
        return {'active': False, 'log_exists': False, **empty, 'samples': [],
                'phase': None, 'phase_detail': None, 'cost_estimate': 0.0,
                'gpu': None, 'price_per_hour': None, 'checkpoint_ready': False}
    log_path = os.path.join(run.staging_dir or '', 'training.log')
    parsed = dict(empty)
    log_exists = bool(run.staging_dir) and os.path.isfile(log_path)
    if log_exists:
        try:
            with open(log_path, encoding='utf-8', errors='replace') as fh:
                parsed.update(lt._parse_training_log(fh.read()))
        except OSError:
            pass
    samples = []
    samples_dir = os.path.join(run.staging_dir or '', 'samples')
    if os.path.isdir(samples_dir):
        for f in os.listdir(samples_dir):
            m = lt._SAMPLE_RE.search(f)
            if m:
                samples.append({'filename': f, 'step': int(m.group(1)),
                                'prompt_idx': int(m.group(2))})
        samples.sort(key=lambda s: s['step'], reverse=True)
    return {'active': run.status in ACTIVE_STATES, 'log_exists': log_exists,
            **parsed, 'samples': samples, **_run_payload(run),
            'phase': run.status}

from remote_yam.public_conversation import request_display, request_text
"""Stateful, no-demo RoboCurve Responses policy over the public YAM gateway.

Wire history follows inspect-robots-agent 0.26.0 _responses.py. The model sees
Cartesian tools; only locally resolved joint-waypoint packets reach AWS.
"""
import base64
import copy
import hashlib
import json
import math
from pathlib import Path
import time
import uuid

from .session import MAX_COMMANDS
from .providers import ResponsesAdapter, PolicyComplete
from .robocurve_contract import SYSTEM_PROMPT, TOOLS
from .robocurve_trajectory import RoboCurveTrajectory, NAMES, InvalidMove


def _unsubmitted_packet_digest(waypoints, call_id=None):
    """Identity of the complete locally prepared packet, without normalization."""
    from .session import MAX_WAYPOINTS_PER_PACKET, _trajectory_waypoints
    if not isinstance(waypoints, list) or not 1 <= len(waypoints) <= MAX_WAYPOINTS_PER_PACKET:
        raise ValueError('Invalid unsubmitted packet')
    # This adapter is also inherited by SO101 and single-arm variants. The
    # transport validates configured robot widths separately; this digest must
    # preserve their exact packet shape rather than assume a YAM model.
    first = waypoints[0]
    if not isinstance(first, dict):
        raise ValueError('Invalid unsubmitted packet')
    counts = tuple(len(first.get(side + '_joints_deg', ())) for side in ('left', 'right'))
    if any(count > 16 for count in counts) or not any(counts):
        raise ValueError('Invalid unsubmitted packet joint counts')
    _trajectory_waypoints(waypoints, counts)
    return hashlib.sha256(json.dumps({'call_id':call_id, 'waypoints':waypoints}, sort_keys=True, separators=(',', ':'),
                                    allow_nan=False).encode()).hexdigest()


class CallRecorder:
    """Local wire JSON plus deduplicated images. Never receives HTTP headers."""
    def __init__(self, root):
        self.path = Path(root) / ('robocurve_' + uuid.uuid4().hex)
        self.path.mkdir(parents=True, mode=0o700)
        (self.path / 'blobs').mkdir(mode=0o700)

    def _pack(self, value):
        if isinstance(value, str) and value.startswith('data:image/') and ';base64,' in value:
            prefix, encoded = value.split(';base64,', 1)
            data = base64.b64decode(encoded, validate=True)
            digest = hashlib.sha256(data).hexdigest()
            blob = self.path / 'blobs' / digest
            if not blob.exists():
                blob.write_bytes(data)
                blob.chmod(0o600)
            return prefix + ';base64,$blob:' + digest
        if isinstance(value, list):
            return [self._pack(v) for v in value]
        if isinstance(value, dict):
            return {k: self._pack(v) for k, v in value.items()}
        return value

    def write(self, kind, **values):
        path = self.path / 'calls.jsonl'
        with path.open('a', encoding='utf-8') as handle:
            handle.write(json.dumps(self._pack({'kind': kind, 'time': time.time(), **values}), allow_nan=False) + '\n')
        path.chmod(0o600)


class RoboCurveResponsesAdapter(ResponsesAdapter):
    supports_runtime_steering = True
    response_speed = 'standard'
    actual_response_speed = None
    def __init__(self, api_key, model, endpoint, *, camera_source=None, recording_root=None):
        super().__init__(api_key, model, endpoint, camera_source=camera_source)
        self._initialize_policy(recording_root)

    def _make_geometry(self):
        return RoboCurveTrajectory()

    def _initialize_policy(self, recording_root):
        """Initialize the motion contract independently of model transport."""
        self._geometry = self._make_geometry()
        from .robocurve_prompts import DEFAULT_PROMPT_VERSION, prompt_text
        self._system_prompt = prompt_text(DEFAULT_PROMPT_VERSION)
        self._behavior_prompt = self._system_prompt
        self._workspace_profile = None
        self._workspace_report_robot_id = None
        self._tools = TOOLS
        self._names = NAMES
        self._camera_names = ('top', 'left', 'right')
        self._history = []
        self._prompt = None
        self._episode = None
        self._pending = None
        self._calls = 0
        self._failures = 0
        self._note = None
        self._outcome = None
        self._recorder = CallRecorder(recording_root) if recording_root is not None else None
        self.cancelled = lambda: False
        self.refresh_observation = None
        self.interaction_sink = None
        self.observation_observer = None
        self.completion_observer = None
        from .steering import SteeringInbox
        self.steering = SteeringInbox(self._interaction)

    def _interaction(self, kind, message, **details):
        if self.interaction_sink:
            self.interaction_sink(kind, message, call=self._calls, **details)

    def set_prompt_version(self, version):
        from .robocurve_prompts import prompt_text
        if self._history:
            raise ValueError('Select the prompt before starting a conversation')
        self._behavior_prompt = prompt_text(version)
        self._refresh_workspace_contract()

    def configure_robot_workspace(self, robot_id, *, report=None):
        """Bind the selected station before queue admission or model calls.

        The saved profile is also used by RGB-only subscription/API transports.
        Other robot embodiments keep their own contracts. Unknown YAM stations
        retain the legacy bounds rather than inheriting another station's box.
        """
        if not isinstance(self._geometry, RoboCurveTrajectory):
            return
        if self._history or self._calls:
            raise ValueError('Select the robot workspace before starting a conversation')
        if self._workspace_report_robot_id not in (None, robot_id):
            raise ValueError('Selected robot differs from the bound workspace calibration')
        if report is not None and report.get('robot_id') != robot_id:
            raise ValueError('Workspace calibration robot mismatch')
        from .controller_workspace import workspace_for_robot
        from .robocurve_trajectory import LOW, HIGH
        profile = workspace_for_robot(robot_id)
        if profile is not None and report is not None:
            profile.validate_report(report)
        # Hosted applications may append startup instructions before admission.
        # Preserve those instructions when binding the first station profile.
        if self._workspace_profile is None:
            self._behavior_prompt = self._system_prompt
        # Rebuild RGB geometry before any observations, applying the station's
        # references once. Depth subclasses own their explicit calibration.
        # Rebinding an unknown station must also clear the previous correction.
        if type(self._geometry) is RoboCurveTrajectory:
            self._geometry = RoboCurveTrajectory(**(profile.rgb_geometry_kwargs() if profile else {}))
        self._geometry.low, self._geometry.high = LOW.copy(), HIGH.copy()
        if profile is not None:
            profile.configure_geometry(self._geometry)
        self._workspace_profile = profile
        if report is not None:
            self._workspace_report_robot_id = robot_id
        self._refresh_workspace_contract()

    def _refresh_workspace_contract(self):
        self._system_prompt = self._behavior_prompt
        if self._workspace_profile is None:
            if isinstance(self._geometry, RoboCurveTrajectory):
                self._tools = TOOLS
            return
        from .robocurve_contract import bounds_text, tools_for_bounds
        low, high = self._geometry.low, self._geometry.high
        self._tools = tools_for_bounds(NAMES, low, high)
        self._system_prompt += (
            '\n\nActive controller workspace for ' + self._workspace_profile.robot_id
            + ' (saved profile ' + self._workspace_profile.profile + '):\n'
            + 'Absolute per-arm base-frame bounds: ' + bounds_text(NAMES, low, high) + '.\n'
            + 'The nominal 0.76 m shoulder reach above describes link geometry, not an allowed target '
            'or guaranteed mechanical reachability. Use these workspace bounds and move_to limits. '
            'Out-of-bounds named targets are rejected locally; do not rely on clamping. '
            'The controller independently checks joint limits, swept poses, table clearance and '
            'collisions; IK and joint pacing also still apply. This saved profile is not live '
            'configuration verification.')

    def public_config(self):
        from .robocurve_prompts import prompt_identity
        identity = prompt_identity(self._system_prompt)
        if self._workspace_profile is not None:
            # Keep the behavioral version while hashing the complete effective prompt.
            identity['prompt_version'] = prompt_identity(self._behavior_prompt)['prompt_version']
        return {**super().public_config(), 'policy': 'robocurve_no_demo',
                **identity,
                **({'controller_workspace': self._workspace_profile.summary()}
                   if self._workspace_profile is not None else {}),
                'response_speed': self.response_speed,
                'actual_response_speed': self.actual_response_speed,
                'model_calls': self._calls, 'history_items': len(self._history),
                'note': self._note, 'outcome': self._outcome,
                'pending_tool': self._pending['call_id'] if self._pending else None,
                'recording_path': str(self._recorder.path) if self._recorder else None}

    def _record(self, kind, **values):
        if self._recorder:
            self._recorder.write(kind, **values)

    def measured_step_displacement(self, start, end):
        """Start-to-end grasp-point translation from measured joints, in metres."""
        import math
        _, before, _ = self._geometry.observe(start)
        _, after, _ = self._geometry.observe(end)
        result = {}
        for side in ('left', 'right'):
            names = [f'{side}_{axis}' for axis in ('x', 'y', 'z')]
            if side == 'left' and 'x' in self._names:
                names = ['x', 'y', 'z']  # Single SO101 uses the left transport arm.
            if not all(name in self._names for name in names):
                continue
            indexes = [self._names.index(name) for name in names]
            values = [float(after[i]) - float(before[i]) for i in indexes]
            if all(math.isfinite(value) for value in values):
                result[side + '_displacement_m'] = math.sqrt(sum(value * value for value in values))
        return result

    def _observation_message(self, prompt, observation, first_step_id):
        _, eef, joints = self._geometry.observe(observation)
        scene = observation.get('planning_scene')
        label = ('Saved home scene for planning only. This is the future starting state, '
                 'not live feedback; execution waits for fresh home and scene validation.'
                 if scene else 'Current observation.')
        text = (label + '\nInstruction: ' + prompt
                + '\nstate[joint_pos]: ' + str([round(float(v), 4) for v in joints])
                + '\nstate[eef_state]: ' + ' '.join(f'{k}={v:.4f}' for k, v in zip(self._names, eef))
                + f'\nGateway waypoints remaining in this session: {MAX_COMMANDS-first_step_id}.')
        content = [{'type': 'input_text', 'text': text}]
        if self._camera_source is None:
            raise RuntimeError('RoboCurve model inference requires a camera frame source')
        self._vision_state = 'capturing'
        self._vision_frames = []
        try:
            frames = {frame.name: frame for frame in self._capture_frames(observation)}
            if set(frames) != set(self._camera_names):
                raise RuntimeError(f'Required camera frames: {self._camera_names}')
            for name in self._camera_names:
                frame = frames[name]
                self._vision_frames.append(frame.summary())
                content.extend([
                    {'type': 'input_text', 'text': f"camera '{name}_cam' (step {first_step_id}):"},
                    {'type': 'input_image', 'image_url': 'data:image/jpeg;base64,' + base64.b64encode(frame.jpeg).decode('ascii'), 'detail': 'high'},
                ])
        except Exception:
            self._vision_state = 'camera_error'
            raise
        # Optional private evidence of selected policy inputs, not transport
        # confirmation. Reuse the exact completed set; never acquire frames or
        # expose prompt, planning-scene contents or camera connection metadata.
        try:
            observer = self.observation_observer
            if observer is not None:
                value = {
                    'schema': 'clawmetry.policy.observation.v1',
                    'frames': [{'camera': name, 'jpeg': bytes(frames[name].jpeg),
                        'source_captured_at_s': frames[name].source_captured_at,
                        'received_at_s': frames[name].received_at} for name in self._camera_names],
                    'first_step_id': first_step_id, 'call_ordinal': self._calls + 1,
                    'observation_step_id': observation.get('step_id'),
                    'observed_at': observation.get('observed_at'),
                    'episode_id': observation.get('episode_id'), 'planning_only': bool(scene),
                }
                if not self.cancelled():
                    observer(value)
        except BaseException:
            # Evidence must not change inference or camera failure behavior.
            pass
        return {'role': 'user', 'content': content}

    def _tool_result(self, call_id, result):
        item = {'type': 'function_call_output', 'call_id': call_id,
                'output': json.dumps(result, allow_nan=False)}
        self._history.append(item)
        self._record('tool_result', item=item)
        message = 'Tool result recorded for the next model call'
        if result.get('ok') is False:
            message = ('Motion stopped before reaching its target: ' if result.get('status') == 'not_reached' else 'Local validation rejected the move; no motion sent: ')+result['error']
        elif result.get('status') == 'give_up':
            message = 'Astra gave up: '+result.get('reason','')
        elif result.get('status') == 'done':
            message = 'Astra reported done: '+result.get('summary','')
        self._interaction('tool_error' if result.get('ok') is False else 'tool_result',
                          message,
                          call_id=call_id, result=result)

    def discard_unsubmitted_trajectory(self, waypoints, *, first_step_id, observation, context):
        """Resolve an exact stale local tool as unexecuted, then permit a new plan.

        Only the trusted controller can establish that zero waypoints were sent.
        This opt-in hook does not infer, capture images, rebuild old targets,
        report completion, change geometry references, or advance a cursor.
        """
        pending = self._pending
        try:
            if (self.cancelled() or not isinstance(pending, dict) or not isinstance(observation, dict)
                    or not isinstance(context, dict) or type(first_step_id) is not int
                    or first_step_id < 0 or first_step_id != pending['first_step_id']
                    or type(observation.get('step_id')) is not int or observation['step_id'] != first_step_id
                    or observation.get('source') != 'hardware' or observation.get('settled') is not True
                    or tuple(observation.get(key) for key in ('episode_id', 'lease_id')) != self._episode
                    or type(context.get('first_step_id')) is not int or context['first_step_id'] != first_step_id
                    or context.get('episode_id') != observation.get('episode_id')
                    or context.get('reason_code') != 'pre_dispatch_pose_changed'
                    or context.get('dispatched') is not False
                    or type(context.get('executed_waypoints')) is not int or context['executed_waypoints'] != 0
                    or not isinstance(context.get('robot_id'), str) or not context['robot_id']
                    or not isinstance(context.get('session_id'), str) or not context['session_id']):
                raise ValueError('Pending tool or source identity changed')
            if any(not isinstance(observation.get(key), str) or not 1 <= len(observation[key]) <= 512
                   for key in ('episode_id', 'lease_id')):
                raise ValueError('Missing measured lease context')
            baseline = dict(step_id=first_step_id, **{key:observation[key] for key in
                ('left_joints_deg', 'right_joints_deg', 'left_gripper', 'right_gripper')})
            if any(type(baseline[key]) not in (int, float) for key in ('left_gripper', 'right_gripper')):
                raise ValueError('Missing measured gripper feedback')
            if any(not isinstance(baseline[side+'_joints_deg'], (list, tuple)) or len(baseline[side+'_joints_deg']) != 6
                   for side in ('left', 'right')):
                raise ValueError('Unsubmitted recovery requires the YAM joint contract')
            _unsubmitted_packet_digest([baseline])
            robots = [observation[key] for key in ('jetson_id', 'robot_id') if key in observation]
            if not robots or any(value != context['robot_id'] for value in robots):
                raise ValueError('Measured robot identity changed')
            if (not isinstance(waypoints, list) or len(waypoints) != pending['waypoint_count']
                    or waypoints[-1].get('step_id') != pending['last_step_id']
                    or waypoints[0].get('step_id') != first_step_id
                    or _unsubmitted_packet_digest(waypoints, pending['call_id']) != pending['packet_sha256']
                    or pending.get('workspace_recovery') is not None):
                raise ValueError('Unsubmitted packet changed')
        except (KeyError, TypeError, ValueError, IndexError, AttributeError, OverflowError):
            raise RuntimeError('Unsubmitted stale packet does not match the pending model tool') from None
        if self.cancelled():
            raise RuntimeError('Unsubmitted stale packet discard cancelled')
        self._tool_result(pending['call_id'], {
            'ok': False, 'status': 'not_executed', 'code': 'pre_dispatch_pose_changed',
            'error': 'Measured joint or gripper pose changed while this packet was being planned. No motion was sent.',
            'steps': 0, 'dispatched': False,
            'instruction': 'Discard this packet and its target. Use the next fresh measured observation and new camera images to choose a new plan. Do not replay this packet. Give up if you cannot proceed safely.'})
        self._pending = None
        return True

    def trajectory_failed(self, code, message, waypoint_count, *, feedback=None):
        """Return verified completion failures or a measured workspace hold."""
        pending = self._pending
        workspace = code in ('left_tip_outside_workspace', 'right_tip_outside_workspace')
        if pending is None or type(waypoint_count) is not int:
            raise RuntimeError('Failed trajectory does not match the pending model tool')
        if workspace:
            if (not isinstance(feedback, dict) or feedback.get('recoverable') is not True
                    or feedback.get('workspace_recovery') != 'held'
                    or feedback.get('hold') != 'measured_position'
                    or type(feedback.get('executed_waypoints')) is not int
                    or feedback['executed_waypoints'] != waypoint_count
                    or not 0 <= waypoint_count <= pending['waypoint_count']
                    or type(feedback.get('next_step_id')) is not int
                    or feedback['next_step_id'] != pending['last_step_id'] + 1):
                raise RuntimeError('Workspace failure has no verified measured hold for the pending model tool')
        elif code not in ('joint_settle_timeout', 'final_position_mismatch') or waypoint_count != pending['waypoint_count']:
            raise RuntimeError('Failed trajectory does not match the pending model tool')
        self._tool_result(pending['call_id'], {
            'ok':False, 'status':'not_reached', 'code':code, 'error':message,
            'steps':waypoint_count,
            **({'feedback':copy.deepcopy(feedback)} if feedback is not None else {}),
            **({'workspace_replacement':copy.deepcopy(pending['workspace_recovery'])}
               if pending.get('workspace_recovery') else {}),
            'instruction':('Workspace boundary reached; only the reported prefix executed and remaining actions were discarded. '
                if workspace else 'Waypoint execution has finished, but the final target was not reached. '
                if code == 'final_position_mismatch' else 'Motion stopped and the arms hold their measured positions. The requested target was not reached. ')
                + 'Use the next fresh observation and images to choose a smaller move or different approach; do not blindly repeat the failed command. Give up if you cannot proceed safely.'})
        self._pending = None

    def trajectory_adjusted(self, details):
        """Retain the gateway replacement until measured completion reports it."""
        pending = self._pending
        changed = details.get('changed_waypoints')
        if (pending is None or details.get('workspace_recovery') != 'adjusted'
                or type(changed) is not int or not 1 <= changed <= pending['waypoint_count']):
            raise RuntimeError('Workspace replacement does not match the pending model tool')
        if pending.get('workspace_recovery') is not None and pending['workspace_recovery'] != details:
            raise RuntimeError('Controller changed the pending model tool workspace replacement')
        pending['workspace_recovery'] = copy.deepcopy(details)

    def trajectory_completed(self, observation, waypoint_count):
        """Controller calls only after acceptance, every progress event and settle."""
        if self._pending is None or waypoint_count != self._pending['waypoint_count']:
            raise RuntimeError('Completed trajectory does not match the pending model tool')
        if observation.get('step_id') != self._pending['last_step_id'] + 1:
            raise RuntimeError('Completed model tool has the wrong observation cursor')
        result = {'ok': True, 'steps': waypoint_count, 'status': 'completed', 'cadence_hz': 10}
        if self._pending.get('workspace_recovery'):
            result.update(feedback=copy.deepcopy(self._pending['workspace_recovery']),
                instruction='The controller executed an adjusted target inside its workspace boundary. '
                    'The original requested motion was changed; inspect replacement feedback and the next measured observation before choosing a new target.')
        self._notify_tracking_completion(observation, waypoint_count)
        self._tool_result(self._pending['call_id'], result)
        self._pending = None
        self._failures = 0

    def _notify_tracking_completion(self, observation, waypoint_count):
        """Optional numerical evidence, not calibration truth or a task reward."""
        try:
            observer, pending = self.completion_observer, self._pending
            if observer is None:
                return
            def state(value, *, target=False):
                result = {}
                if target:
                    step = value.get('step_id')
                    if type(step) is not int or not 0 <= step < 2**63:
                        raise ValueError('Invalid tracking cursor')
                    result['step_id'] = step
                for arm in ('left', 'right'):
                    joints, grip = value.get(arm+'_joints_deg'), value.get(arm+'_gripper')
                    if (not isinstance(joints, (list, tuple)) or len(joints) != 6
                            or any(type(v) not in (int, float) or not math.isfinite(v) for v in joints)
                            or type(grip) not in (int, float) or not math.isfinite(grip) or not 0 <= grip <= 1):
                        raise ValueError('Invalid tracking measurement')
                    result[arm+'_joints_deg'], result[arm+'_gripper'] = list(joints), grip
                return result
            stamp, episode = observation.get('observed_at'), observation.get('episode_id')
            if (type(waypoint_count) is not int or waypoint_count != pending['waypoint_count']
                    or type(self._calls) is not int or self._calls < 1
                    or type(stamp) not in (int, float) or not math.isfinite(stamp) or stamp <= 0
                    or observation.get('settled') is not True
                    or observation.get('source') not in ('hardware', 'simulation')
                    or not isinstance(episode, str) or not 1 <= len(episode) <= 160 or episode != self._episode[0]
                    or type(observation.get('step_id')) is not int or observation['step_id'] != pending['last_step_id']+1
                    or not isinstance(pending['call_id'], str) or not 1 <= len(pending['call_id']) <= 160):
                return
            value = dict(schema='learning.tracking_completion.v1', version=1,
                first_step_id=pending['first_step_id'], last_step_id=pending['last_step_id'],
                waypoint_count=waypoint_count, call_id=pending['call_id'], call_ordinal=self._calls,
                packet_sha256=pending['packet_sha256'], first_target=state(pending['first_target'], target=True),
                final_target=state(pending['final_target'], target=True), measured=state(observation),
                observation_step_id=observation['step_id'], observed_at=stamp, episode_id=episode,
                source=observation['source'], settled=True, workspace_adjusted=bool(pending.get('workspace_recovery')))
            if (type(pending['first_step_id']) is not int or type(pending['last_step_id']) is not int
                    or value['first_target']['step_id'] != pending['first_step_id']
                    or value['final_target']['step_id'] != pending['last_step_id']
                    or pending['last_step_id'] - pending['first_step_id'] + 1 != waypoint_count
                    or not isinstance(value['packet_sha256'], str) or len(value['packet_sha256']) != 64
                    or any(c not in '0123456789abcdef' for c in value['packet_sha256'])):
                return
            if not self.cancelled():
                observer(value)
        except BaseException:
            # Evidence failure, including cancellation checks, cannot replace
            # the original completion/tool-result path or trigger another move.
            pass

    def rebuild_pending_trajectory(self, observation, first_step_id):
        """Resolve the same unexecuted tool target from fresh measured Home."""
        pending = self._pending
        identity = tuple(observation.get(k) for k in ('episode_id', 'lease_id'))
        if (pending is None or identity != self._episode
                or first_step_id != pending['first_step_id']):
            raise RuntimeError('Home rebuild does not match the pending model tool')
        points = self._geometry.build(pending['targets'], observation, first_step_id)
        # Preserve call identity and orientation reference. IK/pacing may change
        # the point count, so completion must use the regenerated packet cursor.
        self._pending = {**pending, 'waypoint_count':len(points),
                         'last_step_id':points[-1]['step_id'],
                         'first_target':copy.deepcopy(points[0]), 'final_target':copy.deepcopy(points[-1]),
                         'packet_sha256':_unsubmitted_packet_digest(points, pending['call_id'])}
        self._record('joint_packet', call=self._calls, cadence_hz=10,
                     rebuilt_from_current_home=True, waypoints=points)
        self._interaction('packet_ready', f'Rebuilt {len(points)} waypoints from current Home',
                          waypoint_count=len(points), first=points[0], last=points[-1])
        return points

    def infer(self, prompt, observation):
        raise RuntimeError('RoboCurve policy requires the joint-waypoint packet transport')

    def build_trajectory(self, prompt, observation, first_step_id):
        self.last_step_model_s = 0.0
        if self._pending is not None:
            raise RuntimeError('Cannot ask the model again before its motion completes')
        if self._outcome is not None:
            raise PolicyComplete(self._outcome['status'])
        identity = tuple(observation.get(k) for k in ('episode_id', 'lease_id'))
        if not self._history:
            self._prompt, self._episode = prompt, identity
            self._history = [{'role': 'system', 'content': self._system_prompt},
                             {'role': 'user', 'content': 'Goal: ' + prompt}]
        elif prompt != self._prompt or identity != self._episode:
            raise RuntimeError('A new trial requires a fresh RoboCurve policy instance')
        while self._calls < 100:
            if self.cancelled():
                return []
            observation_message = self._observation_message(prompt, observation, first_step_id)
            self._history.append(observation_message)
            if self.cancelled():
                return []
            # Put new owner instructions after the fresh observation, so its
            # repeated original task cannot override a later correction.
            self.steering.include(self._history)
            payload = {'model': self.model, 'input': copy.deepcopy(self._history),
                       'tools': copy.deepcopy(self._tools), 'store': False,
                       'include': ['reasoning.encrypted_content']}
            if self.provider_name == 'openai':
                payload['service_tier'] = 'priority' if self.response_speed == 'fast' else 'default'
            self._calls += 1
            self._record('request', call=self._calls, request=payload)
            self._vision_state = 'requesting'
            self._interaction('model_request', f'Model call {self._calls}: waiting for {self.model}',
                              model=self.model, history_items=len(self._history),
                              observation=observation_message['content'][0]['text'],
                              cameras=list(self._vision_frames), prompt=prompt,
                              request_text=request_text(payload), request_display=request_display(payload, self._recorder),
                              images=__import__('remote_yam.public_conversation', fromlist=['request_images']).request_images(observation_message['content'], self._recorder))
            request_started = time.monotonic()
            try:
                raw = self._post_json(payload)
                if self.provider_name == 'openai':
                    tier = raw.get('service_tier')
                    self.actual_response_speed = ('fast' if tier in {'priority', 'fast'}
                                                  else 'standard' if tier == 'default' else None)
            except Exception as exc:
                self._vision_state = 'request_error'
                self._interaction('model_error', str(exc))
                raise
            finally:
                elapsed = time.monotonic() - request_started
                self.last_step_model_s += elapsed
                self._interaction('model_timing', f'Model request: {elapsed:.2f}s', elapsed_s=elapsed)
            self._vision_state = 'response_received'
            self._record('response', call=self._calls, response=raw)
            from .interactions import wire_events
            summary = wire_events([{'kind':'response', 'call':self._calls,
                                    'time':time.time(), 'response':raw}])[0]
            self._interaction('model_response', summary['message'], tools=summary['details']['tools'],
                              response=__import__('remote_yam.public_conversation', fromlist=['response_text']).response_text(raw))
            if self.cancelled():
                return []
            output = raw.get('output')
            if not isinstance(output, list) or any(not isinstance(item, dict) for item in output):
                raise RuntimeError('Model returned malformed Responses output')
            # Preserve the original encrypted reasoning + function-call items.
            # Never synthesize an assistant turn or discard tool-call identity.
            self._history.extend(copy.deepcopy(output))
            calls = [item for item in output if item.get('type') == 'function_call']
            if any(not isinstance(c.get('call_id'), str) or not c['call_id'] for c in calls):
                raise RuntimeError('Model tool call is missing its call_id')
            if len({c['call_id'] for c in calls}) != len(calls):
                raise RuntimeError('Model returned duplicate tool call IDs')
            if self.steering.pending():
                # An update arrived during inference. Resolve every old tool
                # call without executing it, then replan with the new user turn.
                for call in calls:
                    self._tool_result(call['call_id'], {
                        'ok': False, 'status': 'superseded',
                        'error': 'Run-owner steering arrived during inference. This tool was not executed. Replan using the new update.'})
                if callable(getattr(self, 'refresh_observation', None)):
                    observation = self.refresh_observation()
                continue
            try:
                if len(calls) != 1:
                    raise InvalidMove('Respond with exactly one tool call per turn')
                call = calls[0]
                try:
                    args = json.loads(call.get('arguments', ''))
                except (TypeError, ValueError) as exc:
                    raise InvalidMove('Tool arguments must be a JSON object') from exc
                if not isinstance(args, dict):
                    raise InvalidMove('Tool arguments must be a JSON object')
                name = call.get('name')
                if name in ('done', 'give_up'):
                    field = 'summary' if name == 'done' else 'reason'
                    if set(args) != {field, 'hindsight'} or any(not isinstance(v, str) for v in args.values()):
                        raise InvalidMove(f'{name} requires {field} and hindsight strings')
                    self._outcome = {'status': name, **args}
                    self._note = args[field]
                    self._tool_result(call['call_id'], self._outcome)
                    raise PolicyComplete(name)
                if name != 'move_to':
                    raise InvalidMove('Supported tools are move_to, done and give_up')
                if set(args) != {'targets', 'note'} or not isinstance(args.get('note'), str) or not args['note'].strip():
                    raise InvalidMove('move_to requires targets and a nonempty note')
                self._note = args['note']
                points = self._geometry.build(args['targets'], observation, first_step_id)
                self._pending = {'call_id': call['call_id'], 'waypoint_count': len(points),
                                 'last_step_id': points[-1]['step_id'],
                                 'first_step_id':first_step_id, 'targets':copy.deepcopy(args['targets']),
                                 'first_target':copy.deepcopy(points[0]), 'final_target':copy.deepcopy(points[-1]),
                                 'packet_sha256':_unsubmitted_packet_digest(points, call['call_id'])}
                self._record('joint_packet', call=self._calls, cadence_hz=10, waypoints=points)
                self._interaction('packet_ready', f'Prepared {len(points)} joint waypoints at 10 Hz',
                                  waypoint_count=len(points), first=points[0], last=points[-1])
                return points
            except InvalidMove as exc:
                for call in calls:
                    self._tool_result(call['call_id'], {'ok': False, 'error': str(exc),
                                                       'code': exc.code, 'stage':'local_validation', 'steps': 0})
                if not calls:
                    self._history.append({'role': 'user', 'content': str(exc)})
                self._failures += 1
                if self._failures >= 3:
                    raise RuntimeError(f'Model failed three consecutive tool attempts: {exc}') from exc
        raise RuntimeError('RoboCurve model call budget of 100 exhausted')


class OpenAIAdapter(RoboCurveResponsesAdapter):
    provider_name = 'openai'
    response_speed = 'fast'

    def __init__(self, api_key, model, endpoint='https://api.openai.com/v1/responses', **kwargs):
        super().__init__(api_key, model, endpoint, **kwargs)


class AstraAdapter(RoboCurveResponsesAdapter):
    provider_name = 'astra'

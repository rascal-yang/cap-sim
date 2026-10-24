"""Raw HUMANO contact-task onboarding. No apple workflow dependencies.

Saved-state replay is not physical replay. Source motion tokens remain visible.
The button adapter uses the native downward-force/hold checker, not lift gates.
"""
import copy
import inspect
import json
from pathlib import Path
import subprocess
import time
import numpy as np
from .records import create_record
from ..workflow.contracts import file_hash, now
from ..workflow.service import write_new

REPO=Path(__file__).resolve().parents[2]
MODELS=Path('/home/kinetra-4090-01/HUMANO/third_party/gear_sonic_deploy')
SKILL=Path(__file__).parent/'skills/quality_suite/SKILL.md'


def validate_source_clock(times, initial_time, dt, timing):
    t=np.asarray(times,float)
    if timing!='pre_control' or len(t)<2 or not np.isfinite(t).all() or not np.isclose(t[0],initial_time,atol=1e-8,rtol=0) or not np.allclose(np.diff(t),dt,atol=1e-8,rtol=0):
        raise ValueError('Unsupported or misaligned source clock')


def press_segments(times, pressing, hold_steps):
    t=np.asarray(times);mask=np.asarray(pressing,bool)
    if len(t)!=len(mask) or len(t)<2 or np.any(np.diff(t)<=0):raise ValueError('Invalid phase evidence')
    edges=np.diff(np.r_[False,mask,False].astype(int))
    bouts=[(int(a),int(b)-1) for a,b in zip(np.flatnonzero(edges==1),np.flatnonzero(edges==-1)) if b-a>=hold_steps]
    if not bouts:return {'status':'rejected','reason':'No continuous native press hold','segments':[]}
    a,b=bouts[0]
    spans=[('approach',0,a),('press_hold',a,b),('post_contact',b,len(t)-1)]
    return {'status':'ready','segments':[{'name':name,'start_frame':lo,'end_frame':hi,'start_s':float(t[lo]),'end_s':float(t[hi]),'end_inclusive':True} for name,lo,hi in spans], 'boundary_convention':'shared state endpoints; control ticks are not duplicated', 'post_contact_is_not_confirmed_release':True}


def extend_contact_tail(df,hold_steps,reward_dt,policy_dt):
    """Repeat final intent for one native acceptance window, without changing source."""
    import pandas as pd
    n=int(np.ceil(hold_steps*reward_dt/policy_dt))
    out=df.copy(deep=True);out['source_frame']=np.arange(len(out))
    tail=[]
    for i in range(n):
        row=out.iloc[-1].copy();row['sim.time']=float(out['sim.time'].iloc[-1])+(i+1)*policy_dt
        row['sim.qvel']=np.zeros_like(row['sim.qvel']);tail.append(row)
    return pd.concat([out,pd.DataFrame(tail)],ignore_index=True)


def source_paths(dataset,episode):
    root=Path(dataset).resolve();stem=f'episode_{episode:06d}';matches=list(root.glob('data/**/'+stem+'.parquet'))
    if len(matches)!=1:raise ValueError('Expected one source parquet')
    files={'parquet':matches[0],'initial':root/'sonic'/f'{stem}_start.npz','replay':root/'sonic'/f'{stem}_replay.json'}
    for p in files.values():
        if not p.is_file():raise ValueError('Missing source evidence '+str(p))
    return files


def inventory(dataset,episodes):
    import pandas as pd
    rows=[]
    for ep in episodes:
        files=source_paths(dataset,ep);meta=json.loads(files['replay'].read_text());df=pd.read_parquet(files['parquet']);initial=np.load(files['initial'],allow_pickle=False)
        validate_source_clock(df['sim.time'],float(initial['sim_time']),.02,meta['row_timing'])
        if not np.array_equal(initial['qpos'],df['sim.qpos'].iloc[0][:len(initial['qpos'])]):raise ValueError('Initial state differs from pre-control first row')
        qsource=np.stack(df['sim.qpos']);source_tilt=np.rad2deg(np.arccos(np.clip(1-2*(qsource[:,4]**2+qsource[:,5]**2),-1,1)))
        rows.append({'episode':ep,'source_root_height_min_m':float(qsource[:,2].min()),'source_root_tilt_max_deg':float(source_tilt.max()),'default_termination_guard':validate_guard(None),'frames':len(df),'duration_s':len(df)*.02,'historical_accepted':meta.get('accepted'),'historical_provider':meta.get('provider'),'hashes':{k:file_hash(v) for k,v in files.items()}})
    return {'task':Path(dataset).name,'episodes':rows,'physics_steps':0,'historical_success_is_not_new_success':True}


def open_source(dataset,episode,folder,shift=(0,0)):
    import pandas as pd
    from cap_sim.backends.humano import Backend
    from ..privileged import no_physics
    files=source_paths(dataset,episode);meta=json.loads(files['replay'].read_text());df=pd.read_parquet(files['parquet'])
    prepared=Path(folder)/'prepared';prepared.mkdir(exist_ok=True)
    cfg=json.loads(meta['environment_config']);p=prepared/'environment_config.json'
    if not p.exists():write_new(p,cfg)
    task={'name':Path(dataset).name,'resources':{'prepared':str(prepared),'initial_state':str(files['initial']),'sonic_models':str(MODELS)},'scene':{'translation':[*shift,0]}}
    b=Backend()
    with no_physics():b.describe(task)
    validate_source_clock(df['sim.time'],float(b.initial['sim_time']),.02,meta['row_timing'])
    if not np.all(df['sim.nq']==b.m.nq) or not np.all(df['sim.nv']==b.m.nv):raise ValueError('Source dimension mismatch')
    return b,df,files,task


def saved_replay(dataset,episode,root):
    import mujoco
    from ..privileged import no_physics
    folder=Path(root)/f'saved_replay_{episode:06d}'
    if (folder/'result.json').exists():return json.loads((folder/'result.json').read_text())
    folder.mkdir(exist_ok=False);start=now();tick=time.monotonic();b,df,files,task=open_source(dataset,episode,folder)
    try:
        rows=[]
        with no_physics():
            for _,row in df.iterrows():
                b.d.qpos[:]=row['sim.qpos'][:b.m.nq];b.d.qvel[:]=row['sim.qvel'][:b.m.nv];b.d.time=float(row['sim.time']);mujoco.mj_forward(b.m,b.d)
                rows.append(native_metrics(b,None))
        write_new(folder/'frames.json',rows)
        result={'episode':episode,'frames':len(rows),'physics_steps':0,'phase_candidates':{'status':'candidate_only','frames':len(rows)},'contact_frames':sum(r['robot_object_N']>.1 for r in rows),'force_evidence':'recomputed from saved state; not recorded force or new physical success','started_at':start,'ended_at':now(),'wall_s':time.monotonic()-tick,'artifact_path':str(folder),'native_acceptance':native_acceptance(b.e.task),'evidence_summary':summarize_metrics(rows)}
        write_new(folder/'result.json',result);return result
    finally:b.close()


def source_poses(b,df):
    import mujoco
    d=mujoco.MjData(b.m);q=np.stack(df['sim.qpos'])[:,:b.m.nq];v=np.stack(df['sim.qvel'])[:,:b.m.nv]
    poses=[]
    for state in q:
        d.qpos[:]=state;mujoco.mj_kinematics(b.m,d)
        poses.append(np.array([np.r_[d.xpos[i],d.xquat[i]] for i in (b.left,b.right,b.torso)]))
    return q,v,np.asarray(poses)


def decode(s,d,token):
    from cap_sim.backends.native_sonic import rot
    s.history.append({'omega':d.qvel[3:6].copy(),'q':(d.qpos[s.qids]-s.default)[s.order],'dq':d.qvel[s.vids][s.order].copy(),'last':s.last.copy(),'gravity':rot(d.qpos[3:7]).inv().apply([0,0,-1])})
    if len(s.history)!=10:raise ValueError('Missing SONIC history')
    obs=np.concatenate([token]+[np.concatenate([h[k] for h in s.history]) for k in ['omega','q','dq','last','gravity']]).astype(np.float32)
    raw=s.decoder.run(None,{s.decoder.get_inputs()[0].name:obs[None]})[0][0];s.last=raw.copy();s.tick+=1
    return s.default+s.scale*raw[s.reverse]


def encode_reference(s,d,q,v,poses,index,shift,pose_frame=None):
    from cap_sim.backends.native_sonic import rot,quat
    e=np.zeros(1762,np.float32);e[0]=1
    ids=np.minimum(index+np.arange(10)*5,len(q)-1);anchor=rot(q[index,3:7]);actual=rot(d.qpos[3:7])
    e[595:601]=(actual.inv()*anchor).as_matrix()[:,:2].reshape(-1)
    e[661:781]=q[ids][:,s.qids[:12]].reshape(-1);e[781:901]=v[ids][:,s.vids[:12]].reshape(-1)
    ps=[];qs=[]
    for j,offset in enumerate(([.18,-.025,0],[.18,.025,0],[0,0,.35])):
        frame=poses[index] if pose_frame is None else pose_frame
        p=frame[j,:3].copy();r=rot(frame[j,3:])
        if j<2:p[:2]+=shift
        ps.extend(anchor.inv().apply(p+r.apply(offset)-d.qpos[:3]));qs.extend(quat(anchor.inv()*r))
    e[901:910]=ps;e[910:922]=qs
    token=s.encoder.run(None,{s.encoder.get_inputs()[0].name:e[None]})[0][0]
    return token,e


def check_frozen(folder):
    r=json.loads((folder/'experiment.json').read_text())
    if file_hash(folder/'experiment.json')!=(folder/'experiment.sha256').read_text():raise ValueError('Contract changed')
    if r['record_status']!='frozen_ready' or not r['preflight']['passed']:raise ValueError('Preflight incomplete')
    for p,h in r['preflight']['evidence_sha256'].items():
        if file_hash(p)!=h:raise ValueError('Bound evidence changed '+p)
    return r


def token_prefix_steps(mode, contact_start, frames):
    if mode == 'saved_token_replay': return 0
    if mode == 'original_token': return frames
    if mode == 'cartesian_source_legs': return 0
    if mode != 'token_prefix_mode1' or not isinstance(contact_start, int) or not 0 <= contact_start < frames:
        raise ValueError('Invalid explicit controller schedule')
    return contact_start


def uses_original_token(mode, index, prefix):
    return mode == 'original_token' or (mode == 'token_prefix_mode1' and index < prefix)


def physical_case(dataset,episode,root,mode,shift=(0,0),hold_tail=False,decision_path=None,contact_control=False,seed_evidence_path=None,saved_token_case=None,preencoder=False):
    """One frozen rollout or explicitly declared checkpoint branch."""
    import mujoco
    from cap_sim.backends.native_sonic import Sonic
    from humano.mt.base import MotorCommand
    from humano.core.action import ActionCmd
    from .worker import device_lock
    if preencoder and (contact_control or saved_token_case or mode!='token_prefix_mode1'):raise ValueError('Preencoder requires mode1 and forbids saved replay or post-decoder adapter')
    if (mode=='saved_token_replay') != bool(saved_token_case) or (saved_token_case and contact_control):raise ValueError('Saved-token mode requires source and forbids residual controller')
    if mode not in ('original_token','cartesian_source_legs','token_prefix_mode1','saved_token_replay'):raise ValueError('Unsupported explicit mode')
    if decision_path is None:raise ValueError("API decision evidence required")
    with device_lock(wait_s=60) as acquired:
        if not acquired:raise RuntimeError("Physical worker busy")
        return _physical_case(dataset,episode,root,mode,shift,hold_tail,mujoco,Sonic,MotorCommand,ActionCmd,decision_path,contact_control,seed_evidence_path,saved_token_case,preencoder)


def _physical_case(dataset,episode,root,mode,shift,hold_tail,mujoco,Sonic,MotorCommand,ActionCmd,decision_path,contact_control=False,seed_evidence_path=None,saved_token_case=None,preencoder=False):
    from ..cli import create_experiment
    folder=create_experiment(Path(root)/'experiments',Path(dataset).name.replace('G1Wholebody','').replace('Teleop','').lower()+'_'+mode+('_hold' if hold_tail else ''));start=now();tick=time.monotonic()
    b,df,files,task=open_source(dataset,episode,folder,shift)
    try:
        source_frames=len(df)
        decision=json.loads(Path(decision_path).read_text())
        case_skill=Path(decision['origin'].get('skill_path',str(SKILL)))
        params_api=decision['decision'];branch=None;branch_frame=0
        if params_api.get('resume',{}).get('kind')=='checkpoint':
            if not contact_control:raise ValueError('Rollback is available only in the contact route')
            from .retry_state import load
            branch_frame=params_api['resume']['frame'];branch=load(params_api['resume']['case'],branch_frame)
            parent=branch['result']
            if parent['task']!=Path(dataset).name or parent['episode']!=episode or parent['object_delta_xy_m']!=list(shift) or parent['mode']!=mode:raise ValueError('Rollback task/source/scene mismatch')
            parent_plan=json.loads(Path(parent['decision_path']).read_text())['decision']
            for key in ('contact_start','reference_case','criteria_decision','safety_guard'):
                if params_api.get(key)!=parent_plan.get(key):raise ValueError('Rollback fixed contract changed: '+key)
        tail_s=params_api['tail_s'];guard=validate_guard(params_api.get('safety_guard'))
        if tail_s:df=extend_contact_tail(df,round(tail_s/.02),.02,.02)
        hold_tail=bool(tail_s)
        saved_tokens=None;saved_result=None;saved_bound=[]
        if saved_token_case:
            from .saved_token_replay import load_source
            saved_tokens,saved_result,saved_bound=load_source(saved_token_case,len(df),Path(dataset).name,episode,shift)
            if params_api.get('resume',{}).get('kind')=='checkpoint':raise ValueError('Token replay requires full initial-state rollout')
        prefix=token_prefix_steps(mode,params_api['contact_start'],len(df))
        if branch_frame>=len(df):raise ValueError('Rollback frame beyond branch end')
        native_initial={k:copy.deepcopy(v) for k,v in vars(b.e.task).items() if k.startswith('_init_') or k.endswith('_hold_count')}
        if contact_control:
            from .retry_state import task_state
            native_initial=task_state(b.e.task)
        acceptance=native_acceptance(b.e.task)
        if b.reward_stride!=4:raise ValueError('Unsupported native reward cadence')
        s=Sonic(b.m,b.robot,MODELS,b.initial);q,v,poses=source_poses(b,df)
        adapter=None;preadapter=None
        if preencoder:
            from .encoder_wrist import EncoderWrist
            if params_api['contact_control']['joints'] or any(params_api['wrist_delta_m']):raise ValueError('Only preencoder right-wrist corrections permitted')
            preadapter=EncoderWrist(b,s,params_api)
        if contact_control:
            from .contact_control import ContactController
            ref=json.loads((Path(params_api['reference_case'])/'result.json').read_text())
            if ref['task']!=Path(dataset).name or ref['episode']!=episode:raise ValueError('Contact reference identity mismatch')
            adapter=ContactController(b,s,params_api,source_frames)
            write_new(folder/'contact_contract.json',adapter.contract())
        source_tilt=np.rad2deg(np.arccos(np.clip(1-2*(q[:,4]**2+q[:,5]**2),-1,1)))
        if source_tilt.max()>guard['root_tilt_max_deg'] or q[:,2].min()<guard['root_height_min_m']:raise ValueError('Declared termination guard clips the source demonstration; API must explicitly choose a compatible guard or reject this source before physics')
        if mode!='original_token':
            a=params_api['contact_start'];z=params_api['contact_end']
            if any(params_api['wrist_delta_m']):
                if not 0<=a<=z<len(df):raise ValueError('Correction phase outside reference')
                poses[a:z+1,:2,:3]+=np.asarray(params_api['wrist_delta_m'])[None,None,:]
        b.d.time=float(b.initial['sim_time']);b.d.qacc_warmstart[:]=b.initial['qacc_warmstart']
        if branch:
            from .retry_state import restore
            restore(b,s,adapter,branch['states'][branch_frame],branch['metadata'][branch_frame])
        # Runtime check loads the exact frozen models; also record sessions actually used below.
        subprocess.run([str(REPO/'scripts/humano_python.sh'),str(REPO/'scripts/check_humano_runtime.py'),'--load-models','--out',str(folder/'runtime.json')],check=True,stdout=subprocess.DEVNULL,stderr=subprocess.DEVNULL)
        native_source=Path(inspect.getfile(type(b.e.task)))
        native_sources=list(dict.fromkeys(Path(inspect.getfile(cls)) for cls in type(b.e.task).__mro__ if cls.__module__.startswith('humano.')))
        params={k:getattr(b.m,k).tolist() for k in ('body_mass','body_inertia','geom_friction','geom_size','geom_pos','geom_quat','jnt_range','actuator_gainprm','actuator_biasprm')}
        params.update(kp=s.kp.tolist(),kd=s.kd.tolist(),physics_dt_s=float(b.m.opt.timestep),reward_stride=b.reward_stride)
        write_new(folder/'physics.json',params);write_new(folder/'task.json',task);mujoco.mj_saveModel(b.m,str(folder/'scene.mjb'),None)
        if branch:
            if file_hash(folder/'scene.mjb')!=file_hash(branch['case']/'scene.mjb') or json.loads((folder/'physics.json').read_text())!=json.loads((branch['case']/'physics.json').read_text()):raise ValueError('Rollback model/physics changed')
        np.savez_compressed(folder/'initial.npz',qpos=b.d.qpos.copy(),qvel=b.d.qvel.copy(),ctrl=b.d.ctrl.copy(),qacc_warmstart=b.d.qacc_warmstart.copy())
        write_new(folder/'comparison_diff.json',{'object_delta_xy_m':list(shift),'robot_initial_changed':bool(branch),'mode':mode,'hold_tail':hold_tail,'tail_policy_ticks':len(df)-source_frames,'api_parameters':params_api,'source_provider':'historical gpu; current CPU','cartesian_reference':'saved measured wrist poses and saved leg references, not original encoder commands'})
        sources=list((REPO/'humanoid_mimicgen/augmentation').glob('*.py'))+[REPO/'src/cap_sim/backends/humano.py',REPO/'src/cap_sim/backends/native_sonic.py',REPO/'humanoid_mimicgen/privileged.py',case_skill]+native_sources
        bound=[Path(decision_path),Path(decision['origin']['request']),Path(decision['origin']['response'])]+list(files.values())+sources+[folder/n for n in ('runtime.json','physics.json','task.json','scene.mjb','initial.npz','comparison_diff.json')]+list(MODELS.glob('policy/release/*.onnx'))+[MODELS/'planner/target_vel/V2/planner_sonic.onnx']
        bound += saved_bound
        if preadapter:
            bound += preadapter.evidence
            comparison_case=Path(params_api['baseline_case'])
            bound += [comparison_case/n for n in ('scene.mjb','physics.json','initial.npz','result.json')]
        if adapter:bound += adapter.evidence+[folder/'contact_contract.json']
        if branch:bound += branch['evidence']
        seed_evidence=json.loads(Path(seed_evidence_path).read_text()) if seed_evidence_path else None
        if seed_evidence:bound += [Path(seed_evidence_path)]+[Path(p) for p in seed_evidence['evidence_files']]
        snapshot=folder/'source_snapshot';snapshot.mkdir()
        import shutil
        for i,p in enumerate(sources):shutil.copy2(p,snapshot/f'{i:03d}_{p.name}')
        stage={'stage':'whole_episode','mode':mode,'lower_body_interface':'original token decoder' if mode=='original_token' else 'recorded leg q/dq in SONIC mode1 encoder','upper_body_interface':'original token decoder' if mode=='original_token' else 'object-translated world Cartesian wrists and source torso via mode1','action_fields_units_frames':'wrist xyz metres, quaternion wxyz; hand joint radians; q_target radians; torque Nm','target_source':{'path':str(files['parquet']),'tail':f'API-specified final intent for {tail_s} seconds' if hold_tail else 'none'},'interpolation':'50Hz policy, 200Hz PD zero-order hold','ik_used':False,'native_prefix_source_and_hash':{'source':str(files['parquet']),'sha256':file_hash(files['parquet']),'duration_s':len(df)*.02 if mode=='original_token' else 0},'handoff_rule':'none; source initial history restored once'}
        stages=[stage]
        if mode=='token_prefix_mode1':
            stage['stage']='contact_entry_through_end';stage['start_policy_frame']=prefix
            stage['native_prefix_source_and_hash']['duration_s']=prefix*.02
            stage['handoff_rule']='original token ticks [0,start); mode1 ticks [start,end); preserve decoder history, last action and physics state; no blend or reset'
            before=copy.deepcopy(stage);before.update(stage='original_token_approach',start_policy_frame=0,end_policy_frame_exclusive=prefix,mode='original_token',lower_body_interface='original token decoder',upper_body_interface='original token decoder')
            stages=[before,stage]
        r=json.loads((REPO/'docs/experiment-record.template.json').read_text());runtime=json.loads((folder/'runtime.json').read_text())
        r.update(record_status='frozen_ready',experiment_id=folder.name,created_at=start,purpose={'hypothesis':'API-gated multi-task replay and object-relative trajectory retargeting','baseline_paths':[str(files['parquet'])],'planned_changes':[mode,list(shift),{'hold_tail':hold_tail,'tail_policy_ticks':len(df)-source_frames,'api_parameters':params_api}],'invariants':['robot initial state','physics','native acceptance','source hand commands','native reward cadence'],'known_confounders':['source GPU vs current CPU','mode1 uses measured pose references, not source encoder inputs']},cases=[{'episode':episode,'object_delta_xy_m':list(shift)}])
        r['runtime'].update(actual_loaded_session_evidence=str(folder/'runtime.json'),model_hashes=runtime['model_sha256'],python_version='3.10',gear_sonic_package_version=runtime['sonic_package_version'],render_device='not rendered')
        r['physics'].update(simulator_version=mujoco.__version__,robot_and_hand='G1 29DoF Dex3',asset_and_initial_state_manifest={str(p):file_hash(p) for p in (folder/'scene.mjb',folder/'initial.npz')},physics_parameters_manifest=str(folder/'physics.json'),physics_dt_s=.005,control_dt_s=.02,pd_parameters=str(folder/'physics.json'),action_permissions='actuator torque only after single initialization; object shift only at initialization',safety_gates={'root_height_min_m':guard['root_height_min_m'],'root_tilt_max_rad':float(np.deg2rad(guard['root_tilt_max_deg'])),'robot_table_force_N':50,'nonfinite':'stop','mujoco_warning':'stop'},acceptance_source_and_hash={str(p):file_hash(p) for p in native_sources},acceptance_thresholds=acceptance)
        r['control'].update(stage_interfaces=stages,actual_mode_log='execution/controller.npz')
        git=subprocess.run(['git','rev-parse','HEAD'],cwd=REPO,text=True,capture_output=True,check=True).stdout.strip()
        r['pipeline'].update(entrypoint='humanoid_mimicgen.augmentation.suite_physics.physical_case',ordered_steps=['source binding','forward-only setup','loaded runtime','freeze','SONIC rollout','native acceptance','independent saved-state verification','export'],source_snapshot_and_hashes={str(p):file_hash(p) for p in sources},git_commit_and_dirty_patch={'commit':git,'source_snapshot':str(snapshot)},skill_versions_and_hashes=[{str(case_skill):file_hash(case_skill)}],planner_identity_and_prompt_hash={'decision_path':str(decision_path),'sha256':file_hash(decision_path),'origin':decision['origin']},external_model_calls='API orchestrates tools; zero calls inside physics',original_actions_visible=True,feedback_and_reflection_rules='native acceptance and safety only; no online model',allowed_retry_changes=['API-selected source episode, tail seconds or wrist offset interval under new frozen case'],optimization_enabled=False)
        r['budget'].update(attempts_per_case=1,recovery_attempts=0,simulation_seconds_per_attempt=len(df)*.02,feedback_calls=0)
        r['metrics'].update(target_definition='original source wrist pose + object XY shift for Cartesian cases',sampling_and_alignment='source pre-control row; action then four 5ms steps; paired transitions exported',tracking_error_definition='Euclidean actual wrist minus desired world wrist, sampled before policy tick',endpoint_error_definition='last executed reference tracking error; coverage reported separately',orientation_error_definition='not measured',base_drift_definition='final root XY minus source initial XY',failure_truncation_rule='retain failed prefix, never zero-fill')
        r['preflight'].update(passed=True,comparison_diff_path=str(folder/'comparison_diff.json'),evidence_paths=[str(p) for p in bound],evidence_sha256={str(p):file_hash(p) for p in bound})
        if seed_evidence:
            r['pipeline']['decision_reuse']={'source_case':seed_evidence['case'],'source_decision':seed_evidence['decision_path'],'source_api_review':seed_evidence['source_review'],'evidence_path':str(seed_evidence_path),'new_api_plan':False}
            r['pipeline']['external_model_calls']='No new API planning: reexecute immutable prior API decision and require fresh physical validation'
        if adapter:
            r['purpose']['planned_changes'].append(adapter.contract())
            r['control']['stage_interfaces'][-1]['joint_residual_interface']=adapter.contract()
            r['pipeline']['feedback_and_reflection_rules']='API-reviewed criteria; explicit selected-body force admittance and PD/reference corrections; native checker unchanged'
            r['physics']['acceptance_thresholds']['reviewed_shadow']=adapter.audit
            r['physics']['safety_gates']['selected_contact_force_N']=adapter.c['force_stop_N']
        if branch:
            r['purpose']['planned_changes'].append({'checkpoint_branch':params_api['resume'],'inherited_prefix_substeps':branch_frame*4})
            r['purpose']['invariants'].remove('robot initial state')
            r['purpose']['known_confounders'].append('Prefix inherited from ancestor; only suffix newly simulated')
            r['physics']['action_permissions']='one explicit checkpoint restoration at branch initialization; actuator commands only thereafter'
            r['control']['checkpoint_initialization']=params_api['resume']
            r['budget']['recovery_attempts']=1
        if saved_token_case:
            src=Path(saved_token_case)
            if file_hash(folder/'scene.mjb')!=file_hash(src/'scene.mjb') or json.loads((folder/'physics.json').read_text())!=json.loads((src/'physics.json').read_text()):raise ValueError('Replay scene/physics mismatch')
            with np.load(folder/'initial.npz') as x,np.load(src/'initial.npz') as y:
                if set(x.files)!=set(y.files) or any(not np.array_equal(x[k],y[k]) for k in x.files):raise ValueError('Replay initial state mismatch')
            stages[0].update(mode='saved_token_replay',lower_body_interface='saved token directly into original SONIC decoder',upper_body_interface='same decoder; no post-decoder residual; source hand commands',target_source={'case':str(src),'controller_sha256':file_hash(src/'execution/controller.npz')},native_prefix_source_and_hash={'source':str(src/'execution/controller.npz'),'sha256':file_hash(src/'execution/controller.npz'),'duration_s':saved_result['original_token_steps']*.02},handoff_rule='all saved tokens; no encoder calls, mode transitions, or history resets')
            r['purpose'].update(hypothesis='Can newly generated data replay through saved token plus original hand commands and base PD alone?',baseline_paths=[str(src)],planned_changes=['bypass encoder and replay saved tokens','remove all post-decoder joint residuals and PD scaling'],known_confounders=[])
            r['pipeline'].update(external_model_calls='zero new API calls; user-authorized diagnostic using historical parameters only',allowed_retry_changes=[],feedback_and_reflection_rules='decoder proprioception only; no contact correction',entrypoint='saved-token diagnostic through suite_physics.physical_case')
            r['control']['saved_token_replay']={'encoder_calls':0,'planner_calls':0,'residual_calls':0,'base_pd':True,'token_dimension':saved_tokens.shape[1]}
            r['physics']['acceptance_thresholds'].pop('reviewed_shadow',None)
            if 'contact_control' in params_api:r['physics']['safety_gates']['selected_contact_force_N']=params_api['contact_control']['force_stop_N']
        if preadapter:
            if file_hash(folder/'scene.mjb')!=file_hash(comparison_case/'scene.mjb') or json.loads((folder/'physics.json').read_text())!=json.loads((comparison_case/'physics.json').read_text()):raise ValueError('Preencoder baseline scene or physics mismatch')
            with np.load(folder/'initial.npz') as x,np.load(comparison_case/'initial.npz') as y:
                if set(x.files)!=set(y.files) or any(not np.array_equal(x[k],y[k]) for k in x.files):raise ValueError('Preencoder baseline initial mismatch')
            r['purpose'].update(hypothesis='Right-wrist encoder-only correction can press button and yield independently replayable tokens',baseline_paths=[str(comparison_case),str(preadapter.source)],known_confounders=[],planned_changes=['right wrist pre-encoder reference correction only','remove post-decoder joint target and gain corrections',params_api['preencoder']])
            r['control']['stage_interfaces'][-1]['preencoder_right_wrist']={'parameters':params_api['preencoder'],'reference':str(preadapter.source),'force_sensor':'native downward button contact force at pre-control 50Hz','rotation':'world left-multiplied rotation vector; quaternions wxyz','active':'contact_start through end; original token prefix unchanged','post_decoder_changes':False,'fixed_PD':True}
            r['pipeline'].update(feedback_and_reflection_rules='API plans bounded right wrist reference; local force feedback modifies encoder input only',allowed_retry_changes=['new API preencoder parameters under a new frozen case'])
            r['physics']['safety_gates']['selected_contact_force_N']=params_api['contact_control']['force_stop_N']
            r['metrics']['tracking_error_definition']='Legacy source wrist reference diagnostic only; corrected right wrist reference is in execution/preencoder.json and encoder log'
        write_new(folder/'experiment.json',r);(folder/'experiment.sha256').write_text(file_hash(folder/'experiment.json'));check_frozen(folder)
        out=folder/'execution';out.mkdir();prep=time.monotonic()-tick;simtick=time.monotonic();states=[];commands=[];nextstates=[];metrows=[];controllers=[];failure=None;ever=False;initial_time=float(b.d.time);errors=[];checkpoint_states=[];checkpoint_metadata=[]
        if branch:
            n=branch_frame*4;t=branch['trace']
            states=list(t['state'][:n]);commands=list(t['commands'][:n]);nextstates=list(t['next_state'][:n]);errors=list(t['wrist_error_m'][:branch_frame])
            controllers=list(branch['records'][:branch_frame]);metrows=copy.deepcopy(branch['metrics'][:branch_frame]);adapter.logs=copy.deepcopy(branch['logs'][:branch_frame])
            checkpoint_states=list(branch['states'][:branch_frame]);checkpoint_metadata=copy.deepcopy(branch['metadata'][:branch_frame]);ever=bool(branch['metadata'][branch_frame]['ever'])
        for i in range(branch_frame,len(df)):
            row=df.iloc[i]
            if adapter:
                from .retry_state import capture
                state,metadata=capture(b,s,adapter,i,ever);checkpoint_states.append(state);checkpoint_metadata.append(metadata)
            original=uses_original_token(mode,i,prefix)
            if saved_tokens is not None:token=saved_tokens[i];enc=np.zeros(1762,np.float32)
            elif original:token=np.asarray(row['action.motion_token'],np.float32);enc=np.zeros(1762,np.float32)
            else:
                pose_frame=preadapter.apply(poses[i],i) if preadapter else None
                token,enc=encode_reference(s,b.d,q,v,poses,i,np.asarray(shift),pose_frame)
            target=decode(s,b.d,token);controllers.append(np.r_[b.d.time,(-2 if saved_tokens is not None else (-1 if original else 1)),token,enc,target]);errors.append([float(np.linalg.norm(b.d.xpos[b.left]-poses[i,0,:3]-np.r_[shift,0])),float(np.linalg.norm(b.d.xpos[b.right]-poses[i,1,:3]-np.r_[shift,0]))])
            kp,kd=s.kp,s.kd
            if adapter:target,kp,kd=adapter.apply(target,i)
            for sub in range(4):
                states.append(np.r_[b.d.time,b.d.qpos,b.d.qvel])
                b.robot.apply_action(ActionCmd('wbc_torque',low_cmd=MotorCommand(q_target=target,kp=kp,kd=kd),use_sensor=False,left_hand_cmd=MotorCommand.hand_command(np.asarray(row['teleop.left_hand_joints'])),right_hand_cmd=MotorCommand.hand_command(np.asarray(row['teleop.right_hand_joints']))))
                commands.append(np.r_[min(i,source_frames-1),target,b.d.ctrl.copy()]);mujoco.mj_step(b.m,b.d);mujoco.mj_forward(b.m,b.d);nextstates.append(np.r_[b.d.time,b.d.qpos,b.d.qvel])
                if sub==3:
                    info=b.e._get_info();b.e.task.compute_reward(info,mujoco_env=b.e.mujoco);passed=bool(b.e.task.check_success(info,mujoco_env=b.e.mujoco));ever|=passed
                    metrows.append(native_metrics(b,passed))
                    if adapter:metrows[-1]['contact_control']=adapter.measured()
                tilt=np.arccos(np.clip(1-2*(b.d.qpos[4]**2+b.d.qpos[5]**2),-1,1))
                if not np.isfinite(b.d.qpos).all() or not np.isfinite(b.d.qvel).all():failure='nonfinite'
                elif b.d.qpos[2]<guard['root_height_min_m'] or tilt>np.deg2rad(guard['root_tilt_max_deg']):failure='termination_guard_triggered'
                elif any(w.number for w in b.d.warning):failure='simulation_warning'
                elif b.contacts()['robot_table_N']>50:failure='table_collision'
                elif adapter and adapter.force_stop():failure='selected_contact_force_limit'
                elif (saved_token_case or preadapter) and 'contact_control' in params_api:
                    from .contact_control import contact_force
                    c=params_api['contact_control'];f,_=contact_force(b.m,b.d,c['contact_bodies'],b.object_ids.get('target',b.object_ids.get('articulated')))
                    if f>c['force_stop_N']:failure='selected_contact_force_limit'
                if failure:break
            if failure:break
        simwall=time.monotonic()-simtick
        np.savez_compressed(out/'trajectory.npz',state=np.asarray(states),next_state=np.asarray(nextstates),commands=np.asarray(commands),wrist_error_m=np.asarray(errors))
        np.savez_compressed(out/'controller.npz',records=np.asarray(controllers));write_new(out/'metrics.json',metrows)
        if preadapter:write_new(out/'preencoder.json',preadapter.logs)
        if adapter:adapter.save(out);adapter.hold=0;adapter.shadow_ever=False
        # Independently reconstruct contact force and native hold from saved new states.
        for key,value in native_initial.items():setattr(b.e.task,key,copy.deepcopy(value))
        verified=False;verifytick=time.monotonic()
        for index in range(3,len(nextstates),4):
            row=nextstates[index];b.d.qpos[:]=row[1:1+b.m.nq];b.d.qvel[:]=row[1+b.m.nq:];b.d.ctrl[:]=commands[index][-b.m.nu:];b.d.time=row[0];mujoco.mj_forward(b.m,b.d)
            b.e.task.compute_reward(b.e._get_info(),mujoco_env=b.e.mujoco);verified|=bool(b.e.task.check_success(b.e._get_info(),mujoco_env=b.e.mujoco))
            if adapter:adapter.measured()
        independent_wall=time.monotonic()-verifytick
        if verified!=ever:raise ValueError('Independent native checker disagrees')
        providers={k:getattr(s,k).get_providers() for k in ('encoder','decoder','planner')}
        if any(p!=['CPUExecutionProvider'] for p in providers.values()):raise ValueError('Actual provider mismatch')
        success=bool(ever and not failure)
        result={'experiment_id':folder.name,'experiment_path':str(folder),'task':Path(dataset).name,'episode':episode,'mode':mode,'hold_tail':hold_tail,'source_frames':source_frames,'tail_policy_ticks':len(df)-source_frames,'object_delta_xy_m':list(shift),'success':success,'native_success':ever,'termination_guard':guard,'independent_success':verified,'failure':failure,'physics_steps':len(states),'expected_steps':len(df)*4,'coverage':len(states)/(len(df)*4),'started_at':start,'ended_at':now(),'preparation_wall_s':prep,'simulation_wall_s':simwall,'simulation_s':len(states)*.005,'verification_wall_s':independent_wall,'rendering_wall_s':None,'total_wall_s':time.monotonic()-tick,'actual_session_providers':providers,'original_token_steps':sum(int(c[1]==-1) for c in controllers),'encoder_modes':sorted(set(int(c[1]) for c in controllers if c[1]>=0)),'planned_prefix_steps':prefix,'state_initializations':1,'midrun_state_resets':0,'runtime_api_calls':0,'training_ready':False,'retry_count':0,'root_drift_m':float(np.linalg.norm(nextstates[-1][1:3]-states[0][1:3])),'max_downward_force_N':max([r.get('downward_force_N',0) for r in metrows],default=0),'wrist_error_rmse_m':np.sqrt(np.mean(np.asarray(errors)**2,axis=0)).tolist(),'phase_candidates':{'status':'needs_api_annotation','frames':len(metrows),'contact_frames':[i for i,r in enumerate(metrows) if r['robot_object_N']>.1]}}
        if adapter:
            live_shadow=any(m['contact_control']['shadow_success'] for m in metrows)
            if live_shadow!=adapter.shadow_ever:raise ValueError('Independent reviewed checker disagrees')
            result['reviewed_success']=bool(adapter.shadow_ever and not failure) if adapter.shadow_supported else None
            result['reviewed_supported']=adapter.shadow_supported
            result['reviewed_independent_success']=adapter.shadow_ever if adapter.shadow_supported else None
            result['control_variant']='mode1_plus_explicit_joint_contact_residual'
            result['token_alone_replays_execution']=False
        if contact_control:
            result.update(executed_physics_steps=len(states)-branch_frame*4,inherited_physics_steps=branch_frame*4,simulation_s=(len(states)-branch_frame*4)*.005,checkpoint_restorations=int(branch is not None),branch_start_frame=branch_frame,fully_new_rollout=branch is None,native_success_before_branch=bool(branch and branch['metadata'][branch_frame]['ever']),rollback=params_api.get('resume'),lineage=([{'case':str(branch['case']),'prefix_policy_frames':branch_frame,'manifest_sha256':file_hash(branch['case']/'execution/checkpoint_manifest.json')}] if branch else []))
        if preadapter:result.update(preencoder_parameters=params_api['preencoder'],encoder_calls=len(preadapter.logs),planner_calls=0,post_decoder_residual_calls=0,control_variant='mode1_preencoder_right_wrist_fixed_pd',token_alone_replays_execution='pending_independent_replay')
        if saved_token_case:result.update(saved_token_source=str(saved_token_case),saved_token_steps=len(controllers),encoder_calls=0,planner_calls=0,post_decoder_residual_calls=0,control_variant='saved_token_base_pd_source_hands',source_original_token_prefix_steps=saved_result['original_token_steps'])
        result['native_acceptance']=acceptance;result['evidence_summary']=summarize_metrics(metrows);result['decision_path']=str(decision_path)
        write_new(out/'execution_audit.json',result);write_new(folder/'result.json',result)
        if adapter:
            from .retry_state import write_checkpoints
            write_checkpoints(folder,checkpoint_states,checkpoint_metadata)
        check_frozen(folder);return result
    finally:b.close()


def native_acceptance(task):
    sources=[]
    for cls in type(task).__mro__:
        if not cls.__module__.startswith('humano.'):continue
        for name in ('compute_reward','check_success'):
            if name in cls.__dict__:sources.append(inspect.getsource(cls.__dict__[name]))
    params={k:v for k,v in vars(task).items() if not k.startswith('_') and isinstance(v,(int,float,bool,str))}
    constants={}
    for cls in type(task).__mro__:
        if cls.__module__.startswith('humano.'):
            constants.update({k:v for k,v in vars(inspect.getmodule(cls)).items() if k.isupper() and isinstance(v,(int,float))})
    return {'parameters':params,'constants':constants,'validator_code':sources,'validator_owner':type(task).__name__}


def native_metrics(b,passed):
    c=b.contacts();t=b.e.task
    row={'time_s':float(b.d.time),'native_success':passed,**{k:float(v) for k,v in c.items() if k!='events'},'object_xyz':{k:b.d.xpos[v].tolist() for k,v in b.object_ids.items() if k!='table'},'hold_counts':{k:int(v) for k,v in vars(t).items() if k.endswith('_hold_count')}}
    if hasattr(t,'_button_metrics'):
        m=t._button_metrics(mujoco_env=b.e.mujoco)
        row.update(pressing=bool(m['has_downward_button_contact']),downward_force_N=float(m['button_downward_force_n']))
    for name in ('_sit_metrics','_chair_metrics','_dolly_metrics'):
        if hasattr(t,name):
            fn=getattr(t,name);kwargs={'mujoco_env':b.e.mujoco}
            if 'info' in inspect.signature(fn).parameters:kwargs['info']=b.e._get_info()
            m=fn(**kwargs)
            row[name]={k:(bool(v) if isinstance(v,(bool,np.bool_)) else float(v)) for k,v in m.items()}
    return row


def summarize_metrics(rows):
    if not rows:return {}
    longest=current=0
    for row in rows:
        current=current+1 if row.get('pressing',False) else 0;longest=max(longest,current)
    indices=sorted(set(np.linspace(0,len(rows)-1,min(16,len(rows)),dtype=int).tolist()+[i for i,r in enumerate(rows) if r['native_success']][:1]))
    return {'longest_press_s':longest*.02,'peak_robot_object_N':max(r['robot_object_N'] for r in rows),'peak_hand_object_N':max(r['hand_object_N'] for r in rows),'max_hold_counts':{k:max(r['hold_counts'].get(k,0) for r in rows) for k in rows[0]['hold_counts']},'samples':[{'frame':i,**rows[i]} for i in indices]}


def validate_guard(guard):
    if guard is None:return {'root_height_min_m':.3,'root_tilt_max_deg':50.}
    if not isinstance(guard,dict) or set(guard)!={'root_height_min_m','root_tilt_max_deg'}:raise ValueError('Invalid safety guard')
    for key,lo,hi in (('root_height_min_m',.1,.5),('root_tilt_max_deg',30.,100.)):
        value=guard[key]
        if not isinstance(value,(float,int)) or not np.isfinite(value) or not lo<=value<=hi:raise ValueError('Safety guard outside declared experiment budget')
    return guard.copy()

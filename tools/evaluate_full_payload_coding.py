"""Full-payload quantization/zstd characterization; no training/renderer changes.

Uses the previous experiment's binary primitives and metric harness. Decoder
accepts only transmitted files. All quantizer scales are charged in headers.
"""
from __future__ import annotations
import argparse
import json
import sys
from pathlib import Path
import numpy as np
from scipy.spatial.transform import Rotation

ROOT = Path(__file__).resolve().parents[1]
sys.path.insert(0, str(ROOT))
from tools import evaluate_correction_coding as old


class Decoder(old.Decoder):
    def values(self, ref):
        v = super().values(ref)
        if ref.get('transform') == 'absolute_rotvec':
            return Rotation.from_rotvec(v).as_quat()[:, [3, 0, 1, 2]].astype('<f4')
        return v


class Packet(old.Packet):
    segment = None
    def append(self, owner, category, attribute, data, meta):
        label = attribute
        if self.segment is not None:
            label += f'_frame{self.segment}'
        ref = super().append(owner, category, label, data, meta)
        self.labels[ref['file']]['attribute'] = attribute
        return ref


def configurations():
    def cfg(name, p='f32', cp=None, split=True, exact=False, mixed=None):
        return dict(name=name, precision=p, correction_precision=cp or p,
                    split=split, mode='replacement' if exact else 'residual',
                    layout='dense', mixed=mixed or {}, access='gof')
    configs = [cfg('F0_exact_repeated', split=False, exact=True),
               cfg('F0_exact_reuse', exact=True)]
    configs += [cfg('F1_all_'+p,p) for p in ['f16','q16','q12','q10','q8']]
    mixed = dict(xyz='q16', rotation='q12', scale='q12', opacity='q12', sh='q8')
    configs += [cfg('F2_mixed_c'+p, 'q12', p, mixed=mixed) for p in ['q16','q12','q8']]
    configs += [cfg('F3_q12_repeated','q12',split=False)]
    for parent in ['F0_exact_reuse','F1_all_q12','F1_all_q8','F2_mixed_cq8']:
        c = next(c for c in configs if c['name']==parent).copy()
        c.update(name=parent+'_frame_access',access='frame')
        configs.append(c)
    return configs


def serialize(out,cfg,manifest,b,q,schema,seq,life):
    packet=Packet(out/'payloads'/cfg['name'],out/'blob_pool')
    docs=dict(base=dict(format='full-payload-v1',frames=[r['frame'] for r in manifest['frames']],
        shared_count=len(b[0]),new_count=len(q[0])-len(b[0]),ply_fields=list(b[0].dtype.names),
        groups=schema,arrays={}),new=dict(arrays={}),correction=dict(mode=cfg['mode'],config=cfg,arrays={}))
    decoded_base={}
    def emit(owner,a,arrays,p,transform=None):
        fixed=bool(old.static_rows(arrays).all())
        category='static_values' if fixed else 'dynamic_values'
        selected=arrays[:1] if fixed and cfg['split'] else arrays
        maximum=max(float(np.abs(v).max()) for v in arrays)
        refs=[]; decoded=[]
        for fi,v in enumerate(selected):
            packet.segment=fi if cfg['access']=='frame' and len(selected)>1 else None
            data,meta=old.encode_values(v,p,maximum)
            if transform: meta['transform']=transform
            refs.append(packet.append(owner,category,a,data,meta))
            dv=old.decode_values(data,meta)
            if transform: dv=Rotation.from_rotvec(dv).as_quat()[:,[3,0,1,2]]
            decoded.append(dv.astype('<f4'))
        packet.segment=None
        return ({'once':refs[0]} if len(selected)==1 else {'frames':refs}), (decoded*len(arrays) if len(selected)==1 else decoded)
    for owner in ['base','new']:
        for a,arrays in seq[owner].items():
            p=cfg['mixed'].get(a,cfg['precision'])
            transform='absolute_rotvec' if a=='rotation' and cfg['mode']!='replacement' else None
            values=[old.rotation(v).as_rotvec() for v in arrays] if transform else arrays
            schedule,decoded=emit(owner,a,values,p,transform)
            docs[owner]['arrays'][a]=schedule
            if owner=='base': decoded_base[a]=decoded
    correction_lifetimes={}
    for a in schema:
        # Only actual cross-quality state changes are refined. Identical shared
        # scale/SH inherit the quantized base, not a free original checkpoint.
        if all(old.bit_rows_equal(x,y).all() for x,y in zip(seq['base'][a],seq['shared'][a])):
            continue
        values=seq['shared'][a] if cfg['mode']=='replacement' else [
            old.residual(x,y,a) for x,y in zip(decoded_base[a],seq['shared'][a])]
        correction_lifetimes[a]=dict(static_rows=int(old.static_rows(values).sum()),rows=len(values[0]))
        refs,_=emit('correction',a,values,cfg['correction_precision'])
        entry=lambda ref:dict(indices=dict(kind='dense',count=len(b[0])),values=ref)
        docs['correction']['arrays'][a]={'once':entry(refs['once'])} if 'once' in refs else {'frames':[entry(r) for r in refs['frames']]}
    return dict(config=cfg,streams=packet.finish(docs),closed_loop_lifetimes=correction_lifetimes)


original_accounting=old.accounting
def accounting(record):
    result=original_accounting(record)
    for prefix,key in [('raw','raw_bytes'),('zstd','compressed_bytes')]:
        total=result[prefix+'_total_bytes']
        aux=sum(s[key] for s in record['streams'] if s['category'] in ['metadata','index_mask'])
        result[prefix+'_metadata_bytes']=aux
        result[prefix+'_metadata_percent']=100*aux/total
        for owner in ['base','new','correction']:
            value=sum(s[key] for s in record['streams'] if s['owner']==owner and s['category'].endswith('_values'))
            result[f'{prefix}_{owner}_value_bytes']=value
            result[f'{prefix}_{owner}_percent']=100*value/total
        assert total==aux+sum(result[f'{prefix}_{o}_value_bytes'] for o in ['base','new','correction'])
    return result


def report_and_validate(out):
    result=json.loads((out/'summary.json').read_text())
    records=json.loads((out/'payload_index.json').read_text())
    rows=result['variants']; by={r['variant']:r for r in rows}
    import csv
    assert len(list(csv.DictReader((out/'per_view.csv').open())))==len(rows)*80
    assert len(list(csv.DictReader((out/'per_frame.csv').open())))==len(rows)*5
    for r in rows:
        if r['mode']=='replacement':
            assert r['bitwise_state_equal'] and r['global_max_abs_pixel']==0
    checks=[]
    for record in records:
        name=record['config']['name']; folder=out/'payloads'/name
        for s in record['streams']:
            assert (folder/s['file']).stat().st_size==s['raw_bytes']
            assert (folder/(s['file']+'.zst')).stat().st_size==s['compressed_bytes']
            assert old.digest(folder/s['file'])==s['sha256']
            assert old.decompress((folder/(s['file']+'.zst')).read_bytes())==(folder/s['file']).read_bytes()
        if record['config']['access']=='frame':
            parent=name.removesuffix('_frame_access')
            for fi in reversed(range(5)):
                decoder=Decoder(folder)
                state=decoder.frame(fi)
                assert state.tobytes()==Decoder(out/'payloads'/parent).frame(fi).tobytes()
                dynamic_files=[f for f in decoder.cache if '_frame' in f]
                assert all(f'_frame{fi}.bin' in f for f in dynamic_files)
                checks.append(dict(variant=name,frame_index=fi,independent_dynamic_files=dynamic_files))
            for metric in ['gt_psnr','gt_ssim','gt_lpips']:
                assert abs(by[name][metric]-by[parent][metric])<1e-10
    assert all(old.digest(ROOT/p)==h for p,h in result['source_hashes'].items())
    import tempfile
    import os
    for name in ['F0_exact_reuse','F1_all_q12','F2_mixed_cq8_frame_access']:
        source=out/'payloads'/name
        with tempfile.TemporaryDirectory(prefix='compressed_only_',dir=out) as tmp:
            dest=Path(tmp)
            for file in source.glob('*.zst'):
                os.link(file,dest/file.name)
            for fi in range(5):
                assert Decoder(dest).frame(fi).tobytes()==Decoder(source).frame(fi).tobytes()
    validation=dict(passed=True,configurations=len(rows),rendered_view_pairs=len(rows)*80,
        actual_file_sizes_hashes_and_zstd_roundtrip=True,raw_compressed_states_equal=True,
        exact_controls_pixel_and_state_equal=True,independent_access_checks=checks,
        original_sources_unchanged=True,compressed_only_directory_decode=True)
    old.dump(out/'validation.json',validation)
    access=[]
    for r in rows:
        if not r['variant'].endswith('_frame_access'): continue
        base=by[r['variant'].removesuffix('_frame_access')]
        access.append(dict(variant=base['variant'],total_delta_bytes=r['zstd_total_bytes']-base['zstd_total_bytes'],
            total_delta_percent=100*(r['zstd_total_bytes']/base['zstd_total_bytes']-1),
            **{o+'_delta_bytes':r['zstd_'+o+'_value_bytes']-base['zstd_'+o+'_value_bytes'] for o in ['base','new','correction']},
            gof_correction_percent=base['zstd_correction_percent'],frame_correction_percent=r['zstd_correction_percent']))
    old.csv_write(out/'access_comparison.csv',access)
    eligible=[r for r in rows if r['gt_psnr_loss']<=.1 and r['max_view_gt_psnr_loss']<=.25 and r['gt_lpips_increase']<=.0002]
    op=min(eligible,key=lambda r:r['zstd_total_bytes'])
    record=next(r for r in records if r['config']['name']==op['variant'])
    attribute_bytes={a:sum(s['compressed_bytes'] for s in record['streams'] if s['attribute']==a) for a in ['xyz','rotation','scale','opacity','sh']}
    result.update(operating_point=dict(variant=op['variant'],rule='Minimum total bytes with mean PSNR loss <=0.1 dB, worst <=0.25 dB, LPIPS increase <=0.0002; illustrative budget, not perceptual equivalence.',attribute_bytes=attribute_bytes),
        access_comparison=access,script_sha256=old.digest(__file__),helper_sha256=old.digest(old.__file__))
    result['recommendation']='DEPRIORITIZE cross-quality representation redesign as main rate contribution; investigate Base/New dynamic xyz/rotation coding first. Correction is meaningful but secondary at this operating point; broader validation remains necessary.'
    old.dump(out/'summary.json',result)
    lines=['# Full-payload rate–distortion characterization — Longdress', '',
        '## Scope and reproducibility','',
        'Longdress 1051–1055, 41,700 shared + 36,721 new Gaussians, res8/res4 checkpoints; 16 original test cameras/frame (80 views). No retraining, training/model/renderer edits, or learned codec. This is a five-frame, single-sequence characterization, not a general codec result.', '',
        'Run: `conda activate Hoang && python tools/evaluate_full_payload_coding.py`. Existing payloads: append `--render-only`; validation/report only: `--report-only`. Exact upstream renderer extension is loaded from the real experiment’s vendor directory. Source/checkpoint provenance is inherited and checked by `verify_lineage`; source hashes and environment are in summary.json.', '',
        '## Method and accounting','',
        '- Static lifetime is measured bitwise, not assigned by attribute name. All opacity/scale/SH groups are static in these checkpoints; xyz/rotation groups are dynamic. Per-row lifetimes remain in lifetimes.json. Group-static reuse is used for all owners; partially static rows inside dynamic groups are not separately factored in this baseline.',
        '- Base/new: raw quaternion float32 for exact controls; otherwise SO(3) principal rotation vectors, reconstructed to unit wxyz quaternions. Corrections: left-composed SO(3) rotation residual; xyz/opacity use arithmetic residuals. Scale is log-scale, opacity is logit, SH is the checkpoint coefficient representation.',
        '- Closed-loop: correction is calculated against the **decoded quantized Base**, never the original Base hidden at the decoder. Only attributes actually differing between original qualities are refined; identical shared scale/SH inherit lossy Base. New state is independently quantized. Thus shared geometry can be more accurate than suffix geometry; all costs are included.',
        '- Fixed-point signed q8/q10/q12/q16 uses actual packed bits, round-to-nearest-even and separate max-abs calibration per owner/attribute over this GoF. No clipping. Scales are transmitted in JSON. Float16 is IEEE binary16. Mixed config: Base/New xyz q16, rotation/scale/opacity q12, SH q8; correction q16/q12/q8. Mixed choice is a simple preset, not an exhaustive optimization.',
        '- Every binary stream and JSON header is compressed independently with zstd level 6, --long=27, one thread; actual file sizes include zstd headers. GoF-wide groups same owner/lifetime/attribute across five frames. Frame-access groups each dynamic frame independently, plus shared static state/header. Both still use offline GoF calibration; this is **not causal acquisition**.',
        '- Nonoverlapping shares: Base/New/Correction **value bytes** + Metadata (all JSON, quantizer scales, indices/masks). CSV also retains owner-inclusive *_bytes for comparison with prior work; do not add Metadata to those again. Static/dynamic per-owner raw and compressed columns are included. All numbers are logical transmitted sizes, independent of disk hardlinks. MB = 1,000,000 bytes. Cameras, filesystem, transport/container headers outside the specified binary format are excluded consistently.',
        '- Renderer uses original float RGB, clamped [0,1]; original repo SSIM and LPIPS-VGG convention; equal-weight 80-view averages including background. Max/p95 losses are per-view, not per-pixel. Very small metric improvements are not evidence of a better method.', '',
        '## Full rate-quality table','',
        '| Configuration | Base % | New % | Correction % | Metadata % | Total MB | PSNR GT | SSIM | LPIPS | Mean loss dB | p95 / worst dB | PSNR frontier |',
        '|---|---:|---:|---:|---:|---:|---:|---:|---:|---:|---:|---|']
    for r in rows:
        lines.append(f"| {r['variant']} | {r['zstd_base_percent']:.2f} | {r['zstd_new_percent']:.2f} | {r['zstd_correction_percent']:.2f} | {r['zstd_metadata_percent']:.3f} | {r['zstd_total_bytes']/1e6:.6f} | {r['gt_psnr']:.5f} | {r['gt_ssim']:.7f} | {r['gt_lpips']:.7f} | {r['gt_psnr_loss']:.5f} | {r['p95_view_gt_psnr_loss']:.5f} / {r['max_view_gt_psnr_loss']:.5f} | {'yes' if r['pareto_psnr'] else ''} |")
    lines += ['', 'Exact controls above are dense replacement, **not** the previous row-alias best-exact encoder (28.065 MB). The prior exact result is not overwritten and remains a stronger exact coding point. Residual float/quantized states are not claimed bit-exact.', '',
        '## GoF-wide versus frame-access','',
        '| Configuration | Total delta B | Delta % | Base delta B | New delta B | Correction delta B | Correction share GoF → frame |',
        '|---|---:|---:|---:|---:|---:|---|']
    for a in access:
        lines.append(f"| {a['variant']} | {a['total_delta_bytes']:+,} | {a['total_delta_percent']:+.4f} | {a['base_delta_bytes']:+,} | {a['new_delta_bytes']:+,} | {a['correction_delta_bytes']:+,} | {a['gof_correction_percent']:.2f}% → {a['frame_correction_percent']:.2f}% |")
    lines += ['', 'Fresh decoder instances decode each requested frame in reverse order and assert no other frame’s dynamic stream is read. Static streams and global headers are required. This measures frame-dynamic accessibility **within an already initialized GoF**, not arbitrary refresh/rejoin across GoFs or quality switching latency. Negative deltas can occur because separate zstd frames choose different coding tables; they are measured, not clamped to zero.', '',
        '## Operating point and research questions','',
        f"Illustrative operating point: **{op['variant']}**, {op['zstd_total_bytes']/1e6:.6f} MB/GoF, GT PSNR {op['gt_psnr']:.5f}, mean loss {op['gt_psnr_loss']:.5f} dB, worst {op['max_view_gt_psnr_loss']:.5f} dB. Selection: minimum bytes subject to mean loss ≤0.1 dB, worst ≤0.25 dB, LPIPS increase ≤0.0002. This budget does not establish perceptual equivalence.", '',
        f"**A. Correction share:** {op['zstd_correction_percent']:.2f}% of the full coded payload ({op['zstd_correction_value_bytes']:,} value bytes); owner-inclusive {op['zstd_correction_bytes']:,} B. This differs from the old ~2.8% figure with float32 Base/New.", '',
        f"**B. Dominant owner:** Base {op['zstd_base_percent']:.2f}%, New {op['zstd_new_percent']:.2f}%, Correction {op['zstd_correction_percent']:.2f}%; metadata {op['zstd_metadata_percent']:.3f}%.", '',
        '**C. Controlled gain comparisons:**', '']
    for a,b,label in [('F0_exact_repeated','F0_exact_reuse','Static reuse, exact'),('F3_q12_repeated','F1_all_q12','Static reuse, q12'),('F0_exact_reuse','F1_all_q12','Full-payload q12 versus dense exact (includes SO(3)/residual representation change)'),('F1_all_q16','F1_all_q12','Quantization q16 to q12, same representation'),('F2_mixed_cq16','F2_mixed_cq8','Only correction precision, fixed mixed Base/New')]:
        x,y=by[a],by[b]
        lines.append(f"- {label}: raw {x['raw_total_bytes']:,} → {y['raw_total_bytes']:,} B; zstd {x['zstd_total_bytes']:,} → {y['zstd_total_bytes']:,} B ({100*(1-y['zstd_total_bytes']/x['zstd_total_bytes']):.2f}% saving).")
    lines += ['', 'These gains are not additive. Static duplication is mostly already recovered by GoF-wide zstd; static reuse still matters for explicit lifetime/access semantics. Frame-access deltas above isolate the effect of joint temporal compression, not a video prediction codec.', '',
        f"**D. Perfect removal of correction:** optimistic ceiling {op['zstd_correction_percent']:.2f}% from correction values, at most {100*op['zstd_correction_bytes']/op['zstd_total_bytes']:.2f}% including its entire header. This assumes no added state-sharing costs and no quality loss; simply dropping residuals does not achieve this bound.", '',
        '**E. Access penalty:** quantified per configuration above. A five-frame GoF and cached static payload do not establish refresh/rejoin as a bottleneck.', '',
        '**F. Attribute breakdown at the operating point:**', '', '| Attribute | Coded bytes, all owners | Total % |','|---|---:|---:|']
    for a,v in sorted(attribute_bytes.items(),key=lambda x:-x[1]):
        lines.append(f'| {a} | {v:,} | {100*v/op["zstd_total_bytes"]:.2f} |')
    lines += ['', f"**G. Recommendation: DEPRIORITIZE cross-quality representation redesign as the main rate contribution; investigate Base/New dynamic xyz/rotation coding first.** At this operating point Base+New account for {op['zstd_base_percent']+op['zstd_new_percent']:.2f}% of total, while xyz+rotation across owners account for {100*(attribute_bytes['xyz']+attribute_bytes['rotation'])/op['zstd_total_bytes']:.2f}%. Correction is not negligible (~11%, and ~20% at mixed q12), but is secondary at the relaxed operating point. An ideal zero-cost correction removal cannot exceed the ceiling in D. A state-sharing method could remain a secondary refinement, or be justified by separately demonstrated access/quality benefits, but the measured frame-access penalty does not currently supply that justification. This recommendation is conditional on this sequence and quality budget, not a universal rejection.", '',
        'The lossless versus lossy trade-off remains real: uniform q8 saves more bytes but loses 1.62 dB on average and 3.79 dB in the worst view. Mixed q8 correction is a substantially better tested compromise; q12 throughout supports a stricter ~0.01 dB mean-loss point. Tiny GoF/frame byte differences are compressor effects, not evidence that frame segmentation improves representation quality.', '',
        '## Validation and limitations','',
        f"All {len(rows)} configurations × 5 frames × 16 views rendered; raw/zstd decoders agree. Exact controls assert bitwise state equality and pixel equality. File sizes, hashes, decompression, source integrity, and independent frame access validated in validation.json. summary.csv contains raw/compressed owner/lifetime breakdown, GT metrics, vs-original-Q1 PSNR and maximum pixel error; per_view.csv/per_frame.csv preserve distributions; streams.csv provides attribute detail.", '',
        'No optional attribute-video codec is included. ffmpeg is available, but an invertible SO(3)/signed-bit packing and codec pixel-format/precision protocol would add a separate lossy representation and validation axis. The requested main quantization+zstd characterization is complete; these results are not a claim about H.264/H.265 or a final streaming codec.', '',
        'Only five frames, one subject, this camera subset/resolution and these trained checkpoints were evaluated. Group-level reuse leaves partial-row static reuse, alternative transforms/calibration and temporal predictors unexplored. Background-heavy mean metrics need caution. Future general claims require more sequences/GoFs, stronger coding baselines and foreground/tail-quality checks.', '']
    (ROOT/'docs/FULL_PAYLOAD_CODING.md').write_text('\n'.join(lines))


def main():
    parser=argparse.ArgumentParser(description=__doc__)
    parser.add_argument('--output',type=Path,default=ROOT/'output/full_payload_coding')
    parser.add_argument('--render-only',action='store_true')
    parser.add_argument('--report-only',action='store_true')
    args=parser.parse_args();out=args.output.resolve();out.mkdir(parents=True,exist_ok=True)
    if args.report_only:
        report_and_validate(out);return
    manifest_path=ROOT/'output/progressive_gap_real/manifest.json'
    manifest=json.loads(manifest_path.read_text())
    sys.path.insert(0,str(manifest_path.parent/'vendor'))
    old.self_test()
    for bits in [10]:
        values=np.arange(-511,512)
        np.testing.assert_array_equal(old.unpack_signed(old.pack_signed(values,bits),len(values),bits),values)
    hashes={p:old.digest(ROOT/p) for p in ['train.py','render.py','scene/gaussian_model.py','gaussian_renderer/__init__.py']}
    b,q,schema,seq,life=old.collect(manifest)
    old.dump(out/'lifetimes.json',life)
    if args.render_only:
        records=json.loads((out/'payload_index.json').read_text())
    else:
        assert not (out/'payloads').exists(), 'Use new output or --render-only'
        records=[]
        for cfg in configurations():
            record=serialize(out,cfg,manifest,b,q,schema,seq,life);records.append(record)
            print(cfg['name'],accounting(record)['zstd_total_bytes'],flush=True)
        old.dump(out/'payload_index.json',records)
    old.csv_write(out/'streams.csv',[dict(variant=r['config']['name'],**s) for r in records for s in r['streams']])
    old.Decoder=Decoder;old.accounting=accounting
    result=old.evaluate(out,manifest,records,q,schema)
    assert all(old.digest(ROOT/p)==h for p,h in hashes.items())
    import torch,diff_gaussian_rasterization
    result.update(source_hashes=hashes,original_sources_unchanged=True,script_sha256=old.digest(__file__),
        manifest_sha256=old.digest(manifest_path),lifetimes=life,configs=[r['config'] for r in records],
        environment=dict(torch=torch.__version__,gpu=torch.cuda.get_device_name(0),rasterizer=diff_gaussian_rasterization.__file__),
        methodology='Closed-loop residuals against decoded Q0; only genuinely differing shared attribute groups refined. Equal scale/SH inherit quantized Q0. Base/new rotations use absolute SO(3) principal rotvec; corrections compose left SO(3) residuals. Exact controls use raw quaternion replacements. Per-owner/attribute max-abs calibration over GoF, scales transmitted. Nonoverlapping percentages exclude metadata from owner values. Owner-inclusive *_bytes retained separately. Frame-access uses shared static/header plus independent frame dynamic streams; calibration still offline.',
        compressor=dict(executable=old.ZSTD,flags=old.ZSTD_FLAGS))
    old.dump(out/'summary.json',result)
    report_and_validate(out)


if __name__=='__main__':
    main()

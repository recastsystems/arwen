"""Source-pinned WRF 4.7.1 MYNN column solver.

The default WRF 4.6.1 route does not import this module. Source and schema
are generated offline from WRF's public-domain module; native Fortran is
used only by the retained replay recipe, never by a forecast.
"""
from __future__ import annotations

from functools import lru_cache
import hashlib
import json
import os
from pathlib import Path
import shutil
import subprocess

import numpy as np

DATA = Path(__file__).parents[1]/'data'/'mynn471'
BUDGET = ('qshear', 'qbuoy', 'qdiss', 'qwt', 'dqke')
PLUMES = ('edmf_a', 'edmf_w', 'edmf_thl', 'edmf_qt', 'edmf_ent', 'edmf_qc',
          'sub_thl3d', 'sub_sqv3d', 'det_thl3d', 'det_sqv3d')
PHASES = (0, 1, 7, 8, 9, 3, 4, 5, 6)


@lru_cache(maxsize=32)
def schema(nz):
    """Specialize affine array offsets; no CUDA import during planning."""
    first=json.loads((DATA/'schema49.json').read_text())
    second=json.loads((DATA/'schema50.json').read_text())
    def affine(x,y): return x+(y-x)*(int(nz)-49)
    first['nz']=int(nz)
    for name,field in first['arguments'].items():
        if field['type']=='character': continue
        for key in ('count','offset'):
            field[key]=affine(field[key],second['arguments'][name][key])
    for key in first['slab_fields']:
        first['slab_fields'][key]=affine(first['slab_fields'][key],second['slab_fields'][key])
    first['scratch_bytes']=affine(first['scratch_bytes'],second['scratch_bytes'])
    return first


def scratch_shapes(ncol,nz):
    meta=schema(nz)
    # DomainState's shared arena prices FP32 words, including reinterpreted
    # integer and byte storage. Every slot is bounded by the column chunk.
    return {f'mynn471_{slab}': (count*int(ncol),)
            for slab,count in meta['slab_fields'].items()} | {
        'mynn471_work': (meta['scratch_bytes']//4*int(ncol),)}


def diagnostic_shapes(cfg):
    if int(cfg.bl_pbl_physics)!=5: return {}
    result={}
    if cfg.tke_budget:
        for name in BUDGET:
            result[name]=(cfg.nz+(name!='dqke'),cfg.ny,cfg.nx)
    if cfg.bl_mynn_output:
        result.update({name:(cfg.nz,cfg.ny,cfg.nx) for name in PLUMES})
    return result


def source(nz):
    from gpuwm.core.kernels import module_source
    old=module_source('mynn_pbl')
    prefix=old[:old.index('extern "C" __global__')]
    start=old.index('__device__ __forceinline__ real mynn_scale_exponent(')
    end=old.index('// Fortran real**real,',start)
    return (prefix+old[start:end]+FAST_MATH+'\n#define MYNN471_NZ '+str(int(nz))+'\n'
            +(DATA/'model.cu').read_text()+POST_SOURCE)


# Strict mode retains the referee's libm operation order. The regular
# forecast uses CUDA's single-precision elementary functions, as requested
# by fast numerics, rather than paying for the strict helpers' FP64 tables.
FAST_MATH = r'''
#if !GPUWM_WRF_EXACT
#define mynn_glibc_powf powf
#define mynn_glibc_expf expf
#define mynn_glibc_logf logf
#define mynn_glibc_log10f log10f
#define mynn_glibc_atanf atanf
#define mynn_tanhf tanhf
#endif
'''


@lru_cache(maxsize=32)
def image(nz,device,exact):
    import cupy as cp
    text=source(nz)
    from gpuwm.hip_backend import active
    if active():
        # AMD backend: nvcc cannot build a gfx code object. The same source and
        # arithmetic controls go through the shared HIP route (prebuilt lookup,
        # then hiprtc). CUDA keeps the nvcc image route below unchanged.
        from gpuwm.nvrtc_ptx_cache import compile_using_nvrtc
        options=('-std=c++17','--ftz=false','--fmad='+('false' if exact else 'true'),
                 '--prec-div=true','--prec-sqrt=true')+(('-DGPUWM_WRF_EXACT=1',) if exact else ())
        with cp.cuda.Device(device):
            raw,_=compile_using_nvrtc(text,options,None,'mynn471.cu')
            module=cp.cuda.function.Module()
            module.load(raw if isinstance(raw,bytes) else raw.encode())
        names=['mynn471_step'] if exact else ['mynn471_phase'+str(i) for i in PHASES]
        return module,tuple(module.get_function(name) for name in names)
    arch='sm_'+''.join(map(str,cp.cuda.Device(device).compute_capability))
    mode='strict' if exact else 'fast'
    digest=hashlib.sha256(text.encode()).hexdigest()
    filename=f'{arch}-nz{nz}-{mode}-{digest[:16]}.cubin'
    # A checkout reads gpuwm/data/mynn471/images; an install reads the gpuwm-kernels
    # companion, which carries the set (gpuwm.data_assets.VERIFY_ORACLE_TREES).
    from gpuwm.data_assets import verify_oracle_path
    prebuilt=verify_oracle_path('mynn471/images')/filename
    cache=Path(os.environ.get('XDG_CACHE_HOME',str(Path.home()/'.cache')))/'gpuwm'/'mynn471'
    binary=prebuilt if prebuilt.exists() else cache/filename
    if not binary.exists():
        nvcc=shutil.which('nvcc') or '/usr/local/cuda/bin/nvcc'
        if not Path(nvcc).exists():
            raise RuntimeError(f'MYNN 4.7.1 needs its source-bound {arch} nz={nz} {mode} image; '
                               'run the parallel MYNN image prewarm with CUDA nvcc installed')
        cache.mkdir(parents=True,exist_ok=True)
        unit=cache/(filename+'.cu')
        unit.write_text(text)
        temporary=cache/(filename+f'.{os.getpid()}.tmp')
        command=[nvcc,'--cubin','-std=c++17','-arch='+arch,'--ftz=false',
                 '--fmad='+('false' if exact else 'true'),'--prec-div=true',
                 '--prec-sqrt=true','--split-compile=4']
        if exact:command+=['-DGPUWM_WRF_EXACT=1']
        subprocess.run([*command,str(unit),'-o',str(temporary)],check=True)
        temporary.replace(binary)
    # The filename binds the complete numerical source, math helpers,
    # vertical size, architecture and arithmetic mode.
    raw=binary.read_bytes()
    receipt=binary.with_suffix('.json')
    if receipt.exists():
        manifest=json.loads(receipt.read_text())
        if manifest['source_sha256']!=digest or manifest['image_sha256']!=hashlib.sha256(raw).hexdigest():
            raise RuntimeError('MYNN source-bound image receipt does not match '+str(binary))
    elif binary==prebuilt:
        raise RuntimeError('MYNN prebuilt image is missing its source receipt: '+str(binary))
    module=cp.cuda.function.Module()
    module.load(raw)
    names=['mynn471_step'] if exact else ['mynn471_phase'+str(i) for i in PHASES]
    return module,tuple(module.get_function(name) for name in names)


PACK_SOURCE = r'''
template<typename T> __device__ T mynn471_read(const char*p,int type){
 switch(type){
  case 0:return (T)*(const float*)p;
  case 1:return (T)*(const int*)p;
  case 2:return (T)*(const unsigned char*)p;
  case 3:return (T)*(const double*)p;
  case 4:return (T)*(const long long*)p;
  case 5:return (T)*(const unsigned int*)p;
  case 6:return (T)*(const unsigned long long*)p;
 }return (T)0;
}
extern "C" __global__ void mynn471_pack(int n,const unsigned long long *table,
 float *fp,int *ip){
 const unsigned long long *m=table+8*blockIdx.y;
 int k=blockIdx.x*blockDim.x+threadIdx.x;
 if(k>=n*m[2])return;
 int c=k%n,z=k/n;
 unsigned int bits=(unsigned int)m[0];
 unsigned long long dst=m[1]*n+k;
 if(m[5]==0){
   if(m[3]==0)fp[dst]=__uint_as_float(bits);else ip[dst]=(int)bits;
 }else{
   const char *p=(const char*)m[0]+c*m[6]+z*m[7];
   if(m[3]==0)fp[dst]=mynn471_read<float>(p,m[4]);
   else ip[dst]=mynn471_read<int>(p,m[4]);
 }
}
'''


_PACK_TABLES = {}


@lru_cache(maxsize=8)
def pack_kernel(device):
    import cupy as cp
    return cp.RawKernel(PACK_SOURCE,'mynn471_pack',options=('-std=c++17',))


_PACK_CODES = {np.dtype(t): i for i, t in enumerate(('f4', 'i4', 'bool', 'f8', 'i8', 'u4', 'u8'))}
_PACK_LAYOUT = {}


def _pack_layout(meta, skipped=()):
    """Fields in launch order (grouped by element count) and each group's rows."""
    layout = _PACK_LAYOUT.get((id(meta), skipped))
    if layout is None or layout[0] is not meta:
        fields = [(name, f) for name, f in meta['arguments'].items()
                  if f['type'] != 'character' and name not in skipped]
        fields.sort(key=lambda item: item[1]['count'])        # stable: native order within a count
        groups = []; start = 0
        while start < len(fields):
            count = fields[start][1]['count']; stop = start
            while stop < len(fields) and fields[stop][1]['count'] == count:
                stop += 1
            groups.append((count, start, stop)); start = stop
        layout = (meta, fields, groups)
        _PACK_LAYOUT[(id(meta), skipped)] = layout
    return layout[1], layout[2]


def pack_inputs(meta,slabs,arena,values,aliases,scalars,n):
    """Pack all fields, preserving each input's actual strides (one launch per element count).

    The table is built as plain Python rows (per-element numpy assignment
    cost ~1 ms of host time a call), launched in groups of equal element
    count so no grid is padded to the widest field, and its device copy is
    kept per distinct table: the step's value pointers are its stable
    scratch slots, so after the first call there is no host-to-device copy
    (a pageable upload waits for the stream).
    """
    import cupy as cp
    import struct
    # Arguments the column itself clears before any read (schema key
    # initialised_by_column, generated from the driver text) need no packed
    # constant; a state array given for one is still packed.
    cleared = meta.get('initialised_by_column', ())
    skipped = tuple(name for name in cleared
                    if not isinstance(values.get(name, values.get(aliases.get(name, name))), cp.ndarray))
    fields, groups = _pack_layout(meta, skipped)
    rows = []
    for name, f in fields:
        value = values.get(name, values.get(aliases.get(name, name), scalars.get(name, 0)))
        integer = f['slab'] == 'i32'
        if isinstance(value, cp.ndarray):
            if value.ndim > 2:
                raise ValueError('MYNN input rank exceeds two: ' + name)
            shape, strides = value.shape, value.strides
            rows.append((value.data.ptr, f['offset'], f['count'], integer, _PACK_CODES[value.dtype], 1,
                         (strides[0] if shape[0] > 1 else 0) if value.ndim else 0,
                         (strides[1] if shape[1] > 1 else 0) if value.ndim == 2 else 0))
        else:
            bits = (int(value) & 0xFFFFFFFF if integer
                    else struct.unpack('<I', struct.pack('<f', float(value)))[0])
            rows.append((bits, f['offset'], f['count'], integer, 0, 0, 0, 0))
    table = np.array(rows, dtype=np.uint64)
    key = (cp.cuda.Device().id, table.tobytes())
    metadata = _PACK_TABLES.get(key)
    if metadata is None:
        if len(_PACK_TABLES) >= 16:
            _PACK_TABLES.clear()
        metadata = cp.asarray(table)
        _PACK_TABLES[key] = metadata
    kernel = pack_kernel(cp.cuda.Device().id)
    for count, start, stop in groups:
        kernel(((n * count + 127) // 128, stop - start), (128,),
               (np.int32(n), metadata[start:stop], slabs['f32'], slabs['i32']))


def driver(values,*,initflag,delt,scratch=None,closure=2.6,**options):
    import cupy as cp
    n,nz=values['dz'].shape
    meta=schema(nz)
    def buffer(slot,count):
        if scratch is None:return cp.empty(count,dtype=cp.float32)
        return scratch.one(slot,(count,))
    slabs={key:buffer('mynn471_'+key,count*n).reshape(count,n)
           for key,count in meta['slab_fields'].items()}
    slabs['i32']=slabs['i32'].view(cp.int32)
    aliases={'dz1':'dz','u1':'u','v1':'v','w1':'w','th1':'th','p1':'p',
             'ex1':'exner','rho1':'rho','tk1':'tk','kh1':'exch_h','km1':'exch_m','pattern_spp_pbl1':'rstoch'}
    aliases.update({name+'1':name for name in
                    ('sqv','sqc','sqi','sqs','qnc','qni','qnwfa','qnifa','qnbca',
                     'ozone','qke','qke_adv','el','sh','sm','tsq','qsq','cov',
                     'qc_bl','qi_bl','cldfra_bl')})
    scalars=dict(i=1,j=1,initflag=initflag,delt=delt,kts=1,kte=nz,nchem=1,
                 kdvel=1,ndvel=1,closure=closure,bl_mynn_cloudpdf=2,
                 bl_mynn_mixlength=1,bl_mynn_edmf=1,bl_mynn_edmf_mom=1,
                 bl_mynn_edmf_tke=0,bl_mynn_mixscalars=0,bl_mynn_output=0,
                 bl_mynn_cloudmix=1,bl_mynn_mixqt=0,icloud_bl=1,tke_budget=0,
                 flag_qc=True,flag_qi=True)
    scalars.update(options)
    arena=buffer('mynn471_work',n*meta['scratch_bytes']//4).view(cp.uint8)
    pack_inputs(meta,slabs,arena,values,aliases,scalars,n)
    exact=os.environ.get('GPUWM_WRF_EXACT')=='1'
    module,kernels=image(nz,cp.cuda.Device().id,exact)
    if os.environ.get('MYNN471_PHASE_PROOF')=='1':
        kernels=tuple(module.get_function('mynn471_phase'+str(i)) for i in PHASES)
    phases=PHASES if len(kernels)>1 else (-1,)
    threads=32 if exact else 128
    launch_args=(np.int32(n),slabs['f32'],slabs['i32'],arena)
    if len(kernels)>1 and scratch is not None:
        owner=getattr(scratch,'_mynn471_graph_owner',scratch)
        graphs=getattr(owner,'_mynn471_graphs',None)
        if graphs is None:
            graphs={};owner._mynn471_graphs=graphs
        key=(n,nz,exact,cp.cuda.Device().id,arena.data.ptr,
             slabs['f32'].data.ptr,slabs['i32'].data.ptr)
        graph=graphs.get(key)
        if graph is None:
            stream=cp.cuda.Stream(non_blocking=True)
            with stream:
                stream.begin_capture()
                for phase,kernel in zip(phases,kernels):
                    grid=((n+threads-1)//threads,8) if phase==8 else ((n+threads-1)//threads,)
                    kernel(grid,(threads,),launch_args)
                graph=stream.end_capture()
            if len(graphs)>=4:graphs.clear()
            graphs[key]=graph
        graph.launch(stream=cp.cuda.get_current_stream())
    else:
        for phase,kernel in zip(phases,kernels):
            grid=((n+threads-1)//threads,8) if phase==8 else ((n+threads-1)//threads,)
            kernel(grid,(threads,),launch_args)
    def get(name):
        f=meta['arguments'][name]
        result=slabs[f['slab']][f['offset']:f['offset']+f['count']]
        return result.T if f['dims'] else result[0]
    out={name:get(name+'1') for name in
         ('qke','qke_adv','el','sh','sm','tsq','qsq','cov','qc_bl','qi_bl','cldfra_bl')}
    out.update(exch_h=get('kh1'),exch_m=get('km1'),sqv=get('sqv1'))
    for native,target in [('du','rublten'),('dv','rvblten'),('dth','rthblten'),
                          ('dqv','rqvblten'),('dqc','rqcblten'),('dqi','rqiblten'),
                          ('dqs','rqsblten'),('dqnc','rqncblten'),('dqni','rqniblten'),
                          ('dqnwfa','rqnwfablten'),('dqnifa','rqnifablten'),
                          ('dqnbca','rqnbcablten'),('dozone','dozone')]:
        out[target]=get(native+'1')
    out.update({name:get(name) for name in ('pblh','kpbl','maxwidth','maxmf','ztop_plume')})
    # WRF 4.7.1 does not export these two old wrapper diagnostics.
    out['rmol']=values['rmol']
    out['ktop_plume']=cp.zeros(n,dtype=cp.int32)
    if options.get('tke_budget',0):
        out.update({name:get(name+'1') for name in BUDGET})
    if options.get('bl_mynn_output',0):
        out.update({name:get(name.replace('3d','')+'1') for name in PLUMES})
    return out


COPY_SOURCE = r'''
extern "C" __global__ void mynn471_copy(const unsigned long long *table){
 const unsigned long long *m=table+8*blockIdx.y;
 long long rows=(long long)m[2],cols=(long long)m[3];
 long long k=(long long)blockIdx.x*blockDim.x+threadIdx.x;
 if(k>=rows*cols)return;
 long long r=k/cols,c=k%cols;
 char *d=(char*)m[0]+r*(long long)m[4]+c*(long long)m[5];
 const char *s=(const char*)m[1]+r*(long long)m[6]+c*(long long)m[7];
 *(unsigned int*)d=*(const unsigned int*)s;
}
'''
_COPY_TABLES = {}


@lru_cache(maxsize=8)
def copy_kernel(device):
    import cupy as cp
    return cp.RawKernel(COPY_SOURCE, 'mynn471_copy')


def copy_many(pairs):
    """``dst[...] = src`` for every (dst, src) pair in one launch.

    The generated routes hand back ~40 slab views that the PBL wrapper
    writes into the model state; one launch per assignment costs more host
    time than the copies cost the card. Equal shapes and one 4-byte dtype
    per pair (anything else, or a rank above two, uses the plain
    assignment); the words copied are the same words.
    """
    import cupy as cp
    rows = []
    for dst, src in pairs:
        if (dst.shape != src.shape or dst.dtype != src.dtype or dst.dtype.itemsize != 4
                or dst.ndim > 2 or dst.size == 0):
            dst[...] = src
            continue
        if dst.ndim == 1:
            rows.append((dst.data.ptr, src.data.ptr, 1, dst.shape[0], 0, dst.strides[0], 0, src.strides[0]))
        else:
            rows.append((dst.data.ptr, src.data.ptr, dst.shape[0], dst.shape[1],
                         dst.strides[0], dst.strides[1], src.strides[0], src.strides[1]))
    if not rows:
        return
    table = np.array(rows, dtype=np.int64).view(np.uint64)
    key = (cp.cuda.Device().id, table.tobytes())
    device = _COPY_TABLES.get(key)
    if device is None:
        if len(_COPY_TABLES) >= 16:
            _COPY_TABLES.clear()
        device = cp.asarray(table)
        _COPY_TABLES[key] = device
    width = max(r[2] * r[3] for r in rows)
    copy_kernel(cp.cuda.Device().id)(((width + 127) // 128, len(rows)), (128,), (device,))


# WRF 4.7.1 module_bl_mynnedmf_driver.F:878-953 and :666-673.
POST_SOURCE = r'''
extern "C" __global__ void mynn471_post(int count,int nz,int scol,int slev,
 int ocol,int olev,float dt,int cloud,
 const float*qv,const float*qc,const float*qi,const float*sqv,
 float*dqv,float*dqc,float*dqi,float*qcbl,float*qibl){
 int k=blockIdx.x*blockDim.x+threadIdx.x;if(k>=count)return;
 int c=k/nz,z=k%nz,s=c*scol+z*slev,o=c*ocol+z*olev;
 float den=1.f+qv[s];
 float sv=qv[s]/den;
 float next=sv+dqv[o]*dt;
 float rq=next/(1.f-next);
 dqv[o]=(rq-qv[s])/dt;
 float sc=qc[s]/den;
 sc=sc+dqc[o]*dt;
 rq=sc*(1.f+next);
 dqc[o]=(rq-qc[s])/dt;
 float si=qi[s]/den;
 si=si+dqi[o]*dt;
 rq=si*(1.f+next);
 dqi[o]=(rq-qi[s])/dt;
 if(cloud){qcbl[o]=qcbl[o]/(1.f-sqv[o]);qibl[o]=qibl[o]/(1.f-sqv[o]);}
}
'''


def post_run(stage,out,delt,*,icloud):
    import cupy as cp
    n,nz=stage['qv'].shape
    module,_=image(nz,cp.cuda.Device().id,os.environ.get('GPUWM_WRF_EXACT')=='1')
    kernel=module.get_function('mynn471_post')
    count=n*nz
    kernel(((count+127)//128,),(128,),
           (np.int32(count),np.int32(nz),
            *(np.int32(s//4) for s in stage['qv'].strides),
            *(np.int32(s//4) for s in out['sqv'].strides),
            np.float32(delt),np.int32(icloud),
            stage['qv'],stage['qc'],stage['qi'],out['sqv'],
            out['rqvblten'],out['rqcblten'],out['rqiblten'],out['qc_bl'],out['qi_bl']))

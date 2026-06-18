/* cu_fmath.cuh -- fixed-precision elementary functions for cu_fp::cu_freal<PB>.
 *
 * Approach (high-accuracy, NOT correctly-rounded): everything is computed at a
 * working precision W = PB + CU_FGUARD bits (a couple of guard limbs) using
 * Newton iteration (div/sqrt/cbrt) and argument-reduced series (exp/log/trig/
 * hyperbolic), then rounded back to PB.  Results are faithful to ~PB bits and
 * agree with MPFR to <= ~1 ULP in the common range (they are NOT bit-exact:
 * the table-maker's-dilemma cases would need an unbounded Ziv loop, which is
 * incompatible with register-resident fixed precision).  Register-resident, so
 * fastest at low/medium precision; at very high PB the working values spill.
 *
 * Real special functions (gamma, zeta, erf, Bessel, Ai, ...) are intentionally
 * NOT provided here (future work).
 */
#ifndef CU_MPC_CUDA_FMATH_CUH
#define CU_MPC_CUDA_FMATH_CUH

#include "mpc_cuda/cu_freal.cuh"

#ifndef CU_FGUARD
#define CU_FGUARD 128            /* guard bits (multiple of 32) */
#endif

namespace cu_fp {

__host__ __device__ static inline constexpr int
cu_newton_iters (int W){ int k=1, p=52; while(p<W){ p+=p; k++; } return k; }

__host__ __device__ static inline long
cu_floordiv (long a, long b){ long q=a/b, r=a-q*b; if (r!=0 && ((r<0)!=(b<0))) q--; return q; }

/* ---- divide by a small unsigned integer (u < 2^32), correctly rounded ---- */
template<int PB> __host__ __device__ static cu_freal<PB>
cu_div_ui (const cu_freal<PB> &x, unsigned long long u)
{
  typedef cu_freal<PB> F; const int N=F::N;
  if (x.is_zero() || u==1ULL) return x;
  cu_limb q[N+1]; unsigned __int128 rem=0;
  for (int i=N;i>=0;i--){
    cu_limb lo = (i==0)? 0 : x.m[i-1];           /* ext = M << 64 */
    unsigned __int128 acc = (rem<<64) | lo;
    q[i] = (cu_limb)(acc / u); rem = acc % u;
  }
  int hl=-1; for(int i=N;i>=0;i--) if(q[i]){ hl=i; break; }
  if (hl<0){ F r; r.set_zero(); return r; }
  int top=63; { cu_limb v=q[hl]; while(!((v>>top)&1)) top--; }
  int msb=hl*64+top;
  long Ehi = x.exp - (long)N*64 - 64 + msb;
  return F::finalize (q, N+1, msb, Ehi, 0, rem!=0, x.sign);
}

/* ---- Newton reciprocal (full precision of the type) ---- */
template<int W> __host__ __device__ static cu_freal<W>
cu_recip_w (cu_freal<W> b)
{
  int sgn=b.sign; long e=b.exp;
  cu_freal<W> m=b; m.sign=1; m.exp=0;            /* m in [0.5,1) */
  cu_freal<W> z = cu_freal<W>::from_double (1.0 / m.to_double());
  cu_freal<W> two = cu_from_si<W>(2);
  int it = cu_newton_iters(W)+1;
  for (int i=0;i<it;i++)
    z = cu_fmul<W> (z, cu_fsub<W>(two, cu_fmul<W>(m,z)));
  z.sign=sgn; z.exp -= e;
  return z;
}

template<int PB> __host__ __device__ static cu_freal<PB>
cu_fdiv (const cu_freal<PB> &a, const cu_freal<PB> &b)
{
  if (a.is_zero()){ cu_freal<PB> r; r.set_zero(); return r; }
  const int W=PB+CU_FGUARD;
  cu_freal<W> aw=cu_convert<W>(a), bw=cu_convert<W>(b);
  return cu_convert<PB>( cu_fmul<W>(aw, cu_recip_w<W>(bw)) );
}

/* ---- sqrt via Newton rsqrt ---- */
template<int W> __host__ __device__ static cu_freal<W>
cu_sqrt_w (cu_freal<W> x)               /* x>0 */
{
  long e=x.exp, t; cu_freal<W> m=x; m.sign=1;
  if (e & 1L){ m.exp=1; t=(e-1)/2; } else { m.exp=0; t=e/2; }   /* m in [0.5,2) */
  cu_freal<W> y = cu_freal<W>::from_double (1.0 / sqrt(m.to_double()));
  cu_freal<W> three = cu_from_si<W>(3);
  int it = cu_newton_iters(W)+1;
  for (int i=0;i<it;i++){
    cu_freal<W> y2 = cu_fmul<W>(y,y);
    y = cu_scale2<W>( cu_fmul<W>(y, cu_fsub<W>(three, cu_fmul<W>(m,y2))), -1 );
  }
  cu_freal<W> r = cu_fmul<W>(m,y);                /* sqrt(m) = m*rsqrt(m) */
  r.exp += t; return r;
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_sqrt (const cu_freal<PB> &x)
{
  cu_freal<PB> r;
  if (x.is_zero() || x.sign<0){ r.set_zero(); return r; }   /* sqrt(neg) -> 0 (no NaN) */
  const int W=PB+CU_FGUARD;
  return cu_convert<PB>( cu_sqrt_w<W>( cu_convert<W>(x) ) );
}

/* ---- cbrt via Newton rcbrt ---- */
template<int W> __host__ __device__ static cu_freal<W>
cu_cbrt_w (cu_freal<W> x)               /* x>0 */
{
  long e=x.exp; long t=cu_floordiv(e,3); long rem=e-3*t;
  cu_freal<W> m=x; m.sign=1; m.exp=rem;          /* m in [0.5,4) */
  cu_freal<W> y = cu_freal<W>::from_double (1.0 / cbrt(m.to_double()));
  cu_freal<W> four = cu_from_si<W>(4);
  int it = cu_newton_iters(W)+1;
  for (int i=0;i<it;i++){
    cu_freal<W> y3 = cu_fmul<W>( cu_fmul<W>(y,y), y);
    cu_freal<W> c  = cu_div_ui<W>( cu_fsub<W>(four, cu_fmul<W>(m,y3)), 3 );
    y = cu_fmul<W>(y, c);                         /* y *= (4 - m*y^3)/3 */
  }
  cu_freal<W> r = cu_fmul<W>( m, cu_fmul<W>(y,y) ); /* cbrt(m) = m*rcbrt(m)^2 */
  r.exp += t;                                       /* cbrt(x) = cbrt(m)*2^t */
  return r;
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_cbrt (const cu_freal<PB> &x)
{
  cu_freal<PB> r; if (x.is_zero()){ r.set_zero(); return r; }
  const int W=PB+CU_FGUARD;
  cu_freal<W> xw=cu_convert<W>(x); int sgn=xw.sign; xw.sign=1;
  cu_freal<W> rw=cu_cbrt_w<W>(xw); rw.sign=sgn;
  return cu_convert<PB>(rw);
}

/* ---- series helpers (internal): atanh(t), atan(t) for |t|<1 ---- */
template<int W> __host__ __device__ static cu_freal<W>
cu_atanh_series (const cu_freal<W> &t)        /* t + t^3/3 + t^5/5 + ... */
{
  cu_freal<W> t2 = cu_fmul<W>(t,t);
  cu_freal<W> term = t, sum = t;
  unsigned long long k=1;
  for (int n=0;n<3*W;n++){
    term = cu_fmul<W>(term, t2); k+=2;
    cu_freal<W> add = cu_div_ui<W>(term, k);
    sum = cu_fadd<W>(sum, add);
    if (add.is_zero() || add.exp < sum.exp - W - 8) break;
  }
  return sum;
}
template<int W> __host__ __device__ static cu_freal<W>
cu_atan_series (const cu_freal<W> &t)         /* t - t^3/3 + t^5/5 - ... */
{
  cu_freal<W> t2 = cu_fmul<W>(t,t);
  cu_freal<W> term = t, sum = t;
  unsigned long long k=1;
  for (int n=0;n<3*W;n++){
    term = cu_fmul<W>(term, t2); k+=2;
    cu_freal<W> add = cu_div_ui<W>(term, k);
    if (n&1) sum = cu_fadd<W>(sum, add); else sum = cu_fsub<W>(sum, add);
    if (add.is_zero() || add.exp < sum.exp - W - 8) break;
  }
  return sum;
}

/* ---- constants at working precision ---- */
template<int W> __host__ __device__ static cu_freal<W>
cu_const_ln2 ()                                /* 2*atanh(1/3) */
{
  cu_freal<W> third = cu_recip_w<W>( cu_from_si<W>(3) );
  return cu_scale2<W>( cu_atanh_series<W>(third), 1 );
}
template<int W> __host__ __device__ static cu_freal<W>
cu_const_pi ()                                 /* 16 atan(1/5) - 4 atan(1/239) */
{
  cu_freal<W> a5   = cu_atan_series<W>( cu_recip_w<W>( cu_from_si<W>(5) ) );
  cu_freal<W> a239 = cu_atan_series<W>( cu_recip_w<W>( cu_from_si<W>(239) ) );
  return cu_fsub<W>( cu_scale2<W>(a5,4), cu_scale2<W>(a239,2) );  /* 16=*16, 4=*4 */
}

template<int PB> __host__ __device__ static cu_freal<PB> cu_pi (){ return cu_convert<PB>(cu_const_pi<PB+CU_FGUARD>()); }
template<int PB> __host__ __device__ static cu_freal<PB> cu_ln2 (){ return cu_convert<PB>(cu_const_ln2<PB+CU_FGUARD>()); }

/* ===================== Phase 2: exp/log/trig/hyperbolic ===================== */

/* exp at working precision */
template<int W> __host__ __device__ static cu_freal<W>
cu_exp_w (const cu_freal<W> &x)
{
  cu_freal<W> ln2 = cu_const_ln2<W>();
  long k = cu_lround<W>( cu_fmul<W>(x, cu_recip_w<W>(ln2)) );
  cu_freal<W> r = cu_fsub<W>(x, cu_fmul<W>(cu_from_si<W>(k), ln2));   /* |r|<=ln2/2 */
  int mm=0; while (!r.is_zero() && r.exp > -8){ r.exp-=1; mm++; }     /* r/=2^mm */
  cu_freal<W> one=cu_from_si<W>(1), term=one, sum=one; unsigned long long n=0;
  for (int it=0; it<3*W; it++){
    n++; term = cu_div_ui<W>( cu_fmul<W>(term,r), n);
    sum = cu_fadd<W>(sum, term);
    if (term.is_zero() || term.exp < sum.exp - W - 8) break;
  }
  for (int i=0;i<mm;i++) sum=cu_fmul<W>(sum,sum);                     /* ^(2^mm) */
  if (!sum.is_zero()) sum.exp += k;                                  /* *2^k */
  return sum;
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_exp (const cu_freal<PB> &x){
  if (x.is_zero()) return cu_from_si<PB>(1);
  const int W=PB+CU_FGUARD; return cu_convert<PB>( cu_exp_w<W>( cu_convert<W>(x) ) );
}

/* log at working precision (x>0) */
template<int W> __host__ __device__ static cu_freal<W>
cu_log_w (const cu_freal<W> &x)
{
  long E=x.exp; cu_freal<W> m=x; m.sign=1; m.exp=1; long ef=E-1;     /* m in [1,2) */
  if (m.to_double() >= 1.4142135623730951){ m.exp=0; ef+=1; }       /* -> [.707,1.414) */
  cu_freal<W> one=cu_from_si<W>(1);
  cu_freal<W> t = cu_fmul<W>( cu_fsub<W>(m,one), cu_recip_w<W>( cu_fadd<W>(m,one) ) );
  cu_freal<W> logm = cu_scale2<W>( cu_atanh_series<W>(t), 1 );        /* 2*atanh(t) */
  return cu_fadd<W>( cu_fmul<W>(cu_from_si<W>(ef), cu_const_ln2<W>()), logm );
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_log (const cu_freal<PB> &x){
  cu_freal<PB> r; if (x.is_zero()||x.sign<0){ r.set_zero(); return r; }
  const int W=PB+CU_FGUARD; return cu_convert<PB>( cu_log_w<W>( cu_convert<W>(x) ) );
}

/* expm1 / log1p (small-argument safe) */
template<int W> __host__ __device__ static cu_freal<W>
cu_expm1_w (const cu_freal<W> &x)
{
  if (x.is_zero()) return x;
  if (x.exp >= -1){ return cu_fsub<W>( cu_exp_w<W>(x), cu_from_si<W>(1) ); }
  cu_freal<W> term=x, sum=x; unsigned long long n=1;
  for (int it=0; it<3*W; it++){
    n++; term = cu_div_ui<W>( cu_fmul<W>(term,x), n);
    sum = cu_fadd<W>(sum, term);
    if (term.is_zero() || term.exp < sum.exp - W - 8) break;
  }
  return sum;
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_expm1 (const cu_freal<PB> &x){
  if (x.is_zero()) return x;
  const int W=PB+CU_FGUARD; return cu_convert<PB>( cu_expm1_w<W>( cu_convert<W>(x) ) );
}
template<int W> __host__ __device__ static cu_freal<W>
cu_log1p_w (const cu_freal<W> &x)
{
  cu_freal<W> one=cu_from_si<W>(1);
  if (x.exp >= -1) return cu_log_w<W>( cu_fadd<W>(one,x) );
  cu_freal<W> t = cu_fmul<W>( x, cu_recip_w<W>( cu_fadd<W>(x, cu_from_si<W>(2)) ) );
  return cu_scale2<W>( cu_atanh_series<W>(t), 1 );
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_log1p (const cu_freal<PB> &x){
  if (x.is_zero()) return x;
  const int W=PB+CU_FGUARD; return cu_convert<PB>( cu_log1p_w<W>( cu_convert<W>(x) ) );
}

/* sin & cos together (small-r Taylor + double-angle) */
template<int W> __host__ __device__ static void
cu_taylor_sincos (cu_freal<W> r, cu_freal<W> &s, cu_freal<W> &c)
{
  int mm=0; while (!r.is_zero() && r.exp > -8){ r.exp-=1; mm++; }     /* r/=2^mm */
  cu_freal<W> one=cu_from_si<W>(1), r2=cu_fmul<W>(r,r);
  /* cos series */
  c=one; { cu_freal<W> term=one; unsigned long long k=0;
    for (int it=0; it<3*W; it++){
      cu_limb d1=2*k+1, d2=2*k+2; k++;
      term = cu_div_ui<W>( cu_div_ui<W>( cu_fmul<W>(term,r2), d1), d2);
      term.sign=-term.sign; c=cu_fadd<W>(c,term);
      if (term.is_zero() || term.exp < c.exp - W - 8) break; } }
  /* sin series */
  s=r; { cu_freal<W> term=r; unsigned long long k=0;
    for (int it=0; it<3*W; it++){
      cu_limb d1=2*k+2, d2=2*k+3; k++;
      term = cu_div_ui<W>( cu_div_ui<W>( cu_fmul<W>(term,r2), d1), d2);
      term.sign=-term.sign; s=cu_fadd<W>(s,term);
      if (term.is_zero() || term.exp < s.exp - W - 8) break; } }
  for (int i=0;i<mm;i++){                                            /* double angle */
    cu_freal<W> ns = cu_scale2<W>( cu_fmul<W>(s,c), 1 );             /* 2 s c */
    cu_freal<W> nc = cu_fsub<W>( one, cu_scale2<W>( cu_fmul<W>(s,s), 1) ); /* 1-2s^2 */
    s=ns; c=nc;
  }
}
template<int W> __host__ __device__ static void
cu_sincos_w (const cu_freal<W> &x, cu_freal<W> &s, cu_freal<W> &c)
{
  cu_freal<W> pih = cu_scale2<W>( cu_const_pi<W>(), -1 );             /* pi/2 */
  long k = cu_lround<W>( cu_fmul<W>(x, cu_recip_w<W>(pih)) );
  cu_freal<W> r = cu_fsub<W>(x, cu_fmul<W>(cu_from_si<W>(k), pih));   /* |r|<=pi/4 */
  cu_freal<W> sr,cr; cu_taylor_sincos<W>(r,sr,cr);
  switch (((k%4)+4)&3){
    case 0: s=sr; c=cr; break;
    case 1: s=cr; c=cu_neg<W>(sr); break;
    case 2: s=cu_neg<W>(sr); c=cu_neg<W>(cr); break;
    default:s=cu_neg<W>(cr); c=sr; break;
  }
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_sin (const cu_freal<PB> &x){
  if (x.is_zero()) return x;
  const int W=PB+CU_FGUARD; cu_freal<W> s,c; cu_sincos_w<W>(cu_convert<W>(x),s,c);
  return cu_convert<PB>(s);
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_cos (const cu_freal<PB> &x){
  if (x.is_zero()) return cu_from_si<PB>(1);
  const int W=PB+CU_FGUARD; cu_freal<W> s,c; cu_sincos_w<W>(cu_convert<W>(x),s,c);
  return cu_convert<PB>(c);
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_tan (const cu_freal<PB> &x){
  if (x.is_zero()) return x;
  const int W=PB+CU_FGUARD; cu_freal<W> s,c; cu_sincos_w<W>(cu_convert<W>(x),s,c);
  return cu_convert<PB>( cu_fmul<W>(s, cu_recip_w<W>(c)) );
}

/* atan via |x|<=1 reduction + half-angle shrink + series */
template<int W> __host__ __device__ static cu_freal<W>
cu_atan_w (const cu_freal<W> &x)
{
  int sgn=x.sign; cu_freal<W> a=x; a.sign=1;
  bool inv=false; if (a.exp>0 || cu_cmp<W>(a,cu_from_si<W>(1))>0){ a=cu_recip_w<W>(a); inv=true; }
  cu_freal<W> one=cu_from_si<W>(1);
  int red=0;
  for (int i=0;i<10 && a.exp> -4; i++){                              /* a/(1+sqrt(1+a^2)) */
    cu_freal<W> s=cu_sqrt_w<W>( cu_fadd<W>(one, cu_fmul<W>(a,a)) );
    a = cu_fmul<W>(a, cu_recip_w<W>( cu_fadd<W>(one,s) )); red++;
  }
  cu_freal<W> res = cu_scale2<W>( cu_atan_series<W>(a), red );
  if (inv) res = cu_fsub<W>( cu_scale2<W>(cu_const_pi<W>(),-1), res );
  res.sign = res.is_zero()?1:sgn;
  return res;
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_atan (const cu_freal<PB> &x){
  if (x.is_zero()) return x;
  const int W=PB+CU_FGUARD; return cu_convert<PB>( cu_atan_w<W>( cu_convert<W>(x) ) );
}

/* sinh / cosh */
template<int W> __host__ __device__ static cu_freal<W>
cu_sinh_w (const cu_freal<W> &x)
{
  if (x.exp >= -1){ cu_freal<W> ex=cu_exp_w<W>(x);
    return cu_scale2<W>( cu_fsub<W>(ex, cu_recip_w<W>(ex)), -1); }
  cu_freal<W> x2=cu_fmul<W>(x,x), term=x, sum=x; unsigned long long k=0; /* small-x Taylor */
  for (int it=0; it<3*W; it++){
    cu_limb d1=2*k+2, d2=2*k+3; k++;
    term = cu_div_ui<W>( cu_div_ui<W>( cu_fmul<W>(term,x2), d1), d2);
    sum = cu_fadd<W>(sum,term);
    if (term.is_zero() || term.exp < sum.exp - W - 8) break;
  }
  return sum;
}
template<int W> __host__ __device__ static cu_freal<W>
cu_cosh_w (const cu_freal<W> &x){ cu_freal<W> ex=cu_exp_w<W>(x);
  return cu_scale2<W>( cu_fadd<W>(ex, cu_recip_w<W>(ex)), -1); }
template<int PB> __host__ __device__ static cu_freal<PB>
cu_sinh (const cu_freal<PB> &x){ if(x.is_zero())return x;
  const int W=PB+CU_FGUARD; return cu_convert<PB>( cu_sinh_w<W>( cu_convert<W>(x) ) ); }
template<int PB> __host__ __device__ static cu_freal<PB>
cu_cosh (const cu_freal<PB> &x){ if(x.is_zero())return cu_from_si<PB>(1);
  const int W=PB+CU_FGUARD; return cu_convert<PB>( cu_cosh_w<W>( cu_convert<W>(x) ) ); }

/* ===================== Phase 3: asin/acos/atanh/pow ===================== */

template<int W> __host__ __device__ static cu_freal<W>
cu_atanh_w (const cu_freal<W> &x)             /* |x|<1 */
{
  int sgn=x.sign; cu_freal<W> a=x; a.sign=1;
  cu_freal<W> one=cu_from_si<W>(1);
  cu_freal<W> res;
  if (a.exp <= -1) res = cu_atanh_series<W>(a);               /* |a|<=0.5 */
  else { cu_freal<W> t=cu_fmul<W>( cu_fadd<W>(one,a), cu_recip_w<W>( cu_fsub<W>(one,a) ) );
         res = cu_scale2<W>( cu_log_w<W>(t), -1 ); }           /* 0.5*log((1+a)/(1-a)) */
  res.sign = res.is_zero()?1:sgn; return res;
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_atanh (const cu_freal<PB> &x){ if(x.is_zero())return x;
  const int W=PB+CU_FGUARD; return cu_convert<PB>( cu_atanh_w<W>( cu_convert<W>(x) ) ); }

template<int W> __host__ __device__ static cu_freal<W>
cu_asin_w (const cu_freal<W> &x)              /* |x|<=1 */
{
  int sgn=x.sign; cu_freal<W> a=x; a.sign=1;
  cu_freal<W> one=cu_from_si<W>(1);
  cu_freal<W> res;
  if (cu_cmp<W>(a,one) >= 0) res = cu_scale2<W>( cu_const_pi<W>(), -1 );   /* clamp pi/2 */
  else { cu_freal<W> oma2=cu_fsub<W>(one, cu_fmul<W>(a,a));
         cu_freal<W> t=cu_fmul<W>( a, cu_recip_w<W>( cu_sqrt_w<W>(oma2) ) );
         res = cu_atan_w<W>(t); }
  res.sign = res.is_zero()?1:sgn; return res;
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_asin (const cu_freal<PB> &x){ if(x.is_zero())return x;
  const int W=PB+CU_FGUARD; return cu_convert<PB>( cu_asin_w<W>( cu_convert<W>(x) ) ); }

template<int W> __host__ __device__ static cu_freal<W>
cu_acos_w (const cu_freal<W> &x)              /* |x|<=1 -> [0,pi] */
{
  cu_freal<W> one=cu_from_si<W>(1), pih=cu_scale2<W>(cu_const_pi<W>(),-1);
  if (cu_cmp<W>(x,one) >= 0){ cu_freal<W> z; z.set_zero(); return z; }
  if (cu_cmp<W>(x,cu_neg<W>(one)) <= 0) return cu_const_pi<W>();
  return cu_fsub<W>( pih, cu_asin_w<W>(x) );
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_acos (const cu_freal<PB> &x){
  const int W=PB+CU_FGUARD; return cu_convert<PB>( cu_acos_w<W>( cu_convert<W>(x) ) ); }

template<int W> __host__ __device__ static cu_freal<W>
cu_pow_w (const cu_freal<W> &x, const cu_freal<W> &y)
{
  if (y.is_zero()) return cu_from_si<W>(1);
  if (x.is_zero()){ cu_freal<W> z; z.set_zero(); return z; }     /* 0^y (y!=0) */
  if (x.sign>0) return cu_exp_w<W>( cu_fmul<W>(y, cu_log_w<W>(x)) );
  /* x<0: only defined (real) for integer y */
  long yi=cu_lround<W>(y);
  if (cu_cmp<W>(cu_from_si<W>(yi), y)==0){
    cu_freal<W> ax=x; ax.sign=1;
    cu_freal<W> r=cu_exp_w<W>( cu_fmul<W>(y, cu_log_w<W>(ax)) );
    if (yi & 1L) r.sign=-r.sign; return r;
  }
  cu_freal<W> z; z.set_zero(); return z;                          /* NaN substitute */
}
template<int PB> __host__ __device__ static cu_freal<PB>
cu_pow (const cu_freal<PB> &x, const cu_freal<PB> &y){
  const int W=PB+CU_FGUARD;
  return cu_convert<PB>( cu_pow_w<W>( cu_convert<W>(x), cu_convert<W>(y) ) ); }

} /* namespace cu_fp */
#endif /* CU_MPC_CUDA_FMATH_CUH */

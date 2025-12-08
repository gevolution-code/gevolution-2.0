//////////////////////////
// Copyright (c) 2015-2025 Julian Adamek
//
// Permission is hereby granted, free of charge, to any person obtaining a copy
// of this software and associated documentation files (the "Software"), to deal
// in the Software without restriction, including without limitation the rights
// to use, copy, modify, merge, publish, distribute, sublicense, and/or sell
// copies of the Software, and to permit persons to whom the Software is
// furnished to do so, subject to the following conditions:
//  
// The above copyright notice and this permission notice shall be included in
// all copies or substantial portions of the Software.
//  
// THE SOFTWARE IS PROVIDED "AS IS", WITHOUT WARRANTY OF ANY KIND, EXPRESSED OR
// IMPLIED, INCLUDING BUT NOT LIMITED TO THE WARRANTIES OF MERCHANTABILITY,
// FITNESS FOR A PARTICULAR PURPOSE AND NONINFRINGEMENT. IN NO EVENT SHALL THE
// AUTHORS OR COPYRIGHT HOLDERS BE LIABLE FOR ANY CLAIM, DAMAGES OR OTHER
// LIABILITY, WHETHER IN AN ACTION OF CONTRACT, TORT OR OTHERWISE, ARISING FROM,
// OUT OF OR IN CONNECTION WITH THE SOFTWARE OR THE USE OR OTHER DEALINGS IN
// THE SOFTWARE.
//////////////////////////

//////////////////////////
// main.cu
//////////////////////////
// 
// main control sequence of Geneva N-body code with evolution of metric perturbations (gevolution)
//
// Author: Julian Adamek (Université de Genève & Observatoire de Paris & Queen Mary University of London & Universität Zürich)
//
// Last modified: January 2025
//
//////////////////////////

#include <thrust/sort.h>
#include <thrust/device_vector.h>
#include <nvtx3/nvToolsExt.h>
#include <stdlib.h>
#include <set>
#include <vector>
#include <omp.h>
#ifdef HAVE_CLASS
#include "class.h"
#undef MAX			// due to macro collision this has to be done BEFORE including LATfield2 headers!
#undef MIN
#endif
#include "LATfield2.hpp"
#include "metadata.hpp"
#include "class_tools.hpp"
#include "tools.hpp"
#include "background.hpp"
#include "Particles_gevolution.hpp"
#include "gevolution.hpp"
#include "ic_basic.hpp"
#include "ic_read.hpp"
#ifdef ICGEN_PREVOLUTION
#include "ic_prevolution.hpp"
#endif
#ifdef ICGEN_FALCONIC
#include "fcn/togevolution.hpp"
#endif
#ifdef ICGEN_RELIC
#include "ic_relic.hpp"
#endif
#include "radiation.hpp"
#include "parser.hpp"
#include "output.hpp"
#include "hibernation.hpp"
#ifdef VELOCITY
#include "velocity.hpp"
#endif

using namespace std;
using namespace LATfield2;

int main(int argc, char **argv)
{
#ifdef BENCHMARK
	//benchmarking variables
	double ref_time, ref2_time, cycle_start_time;
	double initialization_time;
	double run_time;
	double cycle_time=0;
	double projection_time = 0;
	double snapshot_output_time = 0;
	double spectra_output_time = 0;
	double lightcone_output_time = 0;
	double gravity_solver_time = 0;
	double fft_time = 0;
	int fft_count = 0;   
	double update_q_time = 0;
	int update_q_count = 0;
	double moveParts_time = 0;
	int  moveParts_count = 0;	
#endif  //BENCHMARK
	
	int n = 0, m = 0;
#ifdef EXTERNAL_IO
	int io_size = 0;
	int io_group_size = 0;
#endif
	
	int cycle = 0, snapcount = 0, pkcount = 0, restartcount = 0, usedparams, numparam = 0, numspecies, done_hij;
	int numsteps_ncdm[MAX_PCL_SPECIES-2];
	long numpts3d;
	int box[3];
	double dtau, dtau_old, dx, tau, a, fourpiG, tmp, start_time;
	double maxvel[MAX_PCL_SPECIES];
	FILE * outfile;
	char filename[2*PARAM_MAX_LENGTH+24];
	string h5filename;
	char * settingsfile = NULL;
	char * precisionfile = NULL;
	parameter * params = NULL;
	metadata sim;
	cosmology cosmo;
	icsettings ic;
	double T00hom = 0.;
	Real phi_hom;

#ifdef ANISOTROPIC_EXPANSION
	Real hij_hom[5] = {0.,0.,0.,0.,0.}; // hij_hom = {h_00, h_01, h_02, h_11, h_12} - only the symmetric part of the tensor is stored, h_33 = -h_00-h_11 due to the tracelessness condition
	Real hijprime_hom[5] = {0.,0.,0.,0.,0.}; // hijprime_hom = {h_00', h_01', h_02', h_11', h_12'}
#endif

#ifndef H5_DEBUG
	H5Eset_auto2 (H5E_DEFAULT, NULL, NULL);
#endif
	
	for (int i = 1 ; i < argc ; i++){
		if ( argv[i][0] != '-' )
			continue;
		switch(argv[i][1]) {
			case 's':
				settingsfile = argv[++i]; //settings file name
				break;
			case 'n':
				n = atoi(argv[++i]); //size of the dim 1 of the processor grid
				break;
			case 'm':
				m =  atoi(argv[++i]); //size of the dim 2 of the processor grid
				break;
			case 'p':
#ifndef HAVE_CLASS
				cout << "HAVE_CLASS needs to be set at compilation to use CLASS precision files" << endl;
				exit(-100);
#endif
				precisionfile = argv[++i];
				break;
			case 'i':
#ifndef EXTERNAL_IO
				cout << "EXTERNAL_IO needs to be set at compilation to use the I/O server"<<endl;
				exit(-1000);
#else
				io_size =  atoi(argv[++i]);
#endif
				break;
			case 'g':
#ifndef EXTERNAL_IO
				cout << "EXTERNAL_IO needs to be set at compilation to use the I/O server"<<endl;
				exit(-1000);
#else
				io_group_size = atoi(argv[++i]);
#endif
		}
	}

#ifndef EXTERNAL_IO
	parallel.initialize(n,m);
#else
	if (!io_size || !io_group_size)
	{
		cout << "invalid number of I/O tasks and group sizes for I/O server (-DEXTERNAL_IO)" << endl;
		exit(-1000);
	}
	parallel.initialize(n,m,io_size,io_group_size);
	if(parallel.isIO()) ioserver.start();
	else
	{
#endif
	
	COUT << COLORTEXT_WHITE << endl;	
	COUT << "  _   _      _         __ ,  _" << endl;
	COUT << " (_| (-' \\/ (_) (_ (_| (  ( (_) /\\/	version 2.0 alpha    running on " << n*m << " tasks with " << omp_get_max_threads() << " OpenMP threads per task." << endl;
	COUT << "  -'" << endl << COLORTEXT_RESET << endl;

	int deviceCount;
	cudaGetDeviceCount(&deviceCount);

	if (deviceCount == 0)
	{
		COUT << COLORTEXT_RED << " error" << COLORTEXT_RESET << ": no CUDA-capable device found!" << endl;
		parallel.abortForce();
	}

	for (int device = 0; device < deviceCount; ++device)
	{
		cudaDeviceProp deviceProp;
		cudaGetDeviceProperties(&deviceProp, device);
		COUT << " Device " << device << ": " << deviceProp.name << " with " << deviceProp.multiProcessorCount << " SMs, CC " << deviceProp.major << "." << deviceProp.minor << ", global memory " << deviceProp.totalGlobalMem / (1024*1024) << " MB" << endl << endl;
	}
	
#if GRADIENT_ORDER > 1
	COUT << " compiled with GRADIENT_ORDER=" << GRADIENT_ORDER << endl;
#endif
#ifdef CIC_PROJECT_TIJ
	COUT << " compiled with CIC_PROJECT_TIJ" << endl;
#endif
	
	if (settingsfile == NULL)
	{
		COUT << COLORTEXT_RED << " error" << COLORTEXT_RESET << ": no settings file specified!" << endl;
		parallel.abortForce();
	}
	
	COUT << " initializing..." << endl;
	
	start_time = MPI_Wtime();
	
	numparam = loadParameterFile(settingsfile, params);
	
	usedparams = parseMetadata(params, numparam, sim, cosmo, ic);
	
	COUT << " parsing of settings file completed. " << numparam << " parameters found, " << usedparams << " were used." << endl;
	
	sprintf(filename, "%s%s_settings_used.ini", sim.output_path, sim.basename_generic);
	saveParameterFile(filename, params, numparam);
	
	free(params);

#ifdef HAVE_CLASS
	cosmo.Hspline = NULL;

	background class_background;
  	perturbs class_perturbs;
  	
  	if (precisionfile != NULL)
	  	numparam = loadParameterFile(precisionfile, params);
	else
#endif
		numparam = 0;
	
	h5filename.reserve(2*PARAM_MAX_LENGTH);
	h5filename.assign(sim.output_path);
	
	box[0] = sim.numpts;
	box[1] = sim.numpts;
	box[2] = sim.numpts;
	
	Lattice lat(3,box,GRADIENT_ORDER);
	Lattice latFT;
	latFT.initializeRealFFT(lat,0);
	
	perfParticles_gevolution<part_simple,part_simple_info> pcls_cdm;
	perfParticles_gevolution<part_simple,part_simple_info> pcls_b;
	Particles_gevolution<part_simple,part_simple_info,part_simple_dataType> * pcls_ncdm = nullptr;
	if (cosmo.num_ncdm > 0) pcls_ncdm = new Particles_gevolution<part_simple,part_simple_info,part_simple_dataType>[cosmo.num_ncdm];

	Field<Real> * update_cdm_fields[3];
	Field<Real> * update_b_fields[3];
	Field<Real> * update_ncdm_fields[3];
	Field<Real> * project_Tij_fields[2];
	Field<Real> * project_T0i_fields[2];
	double f_params[7] = {0., 0., 0., 0., 0., 0., 0.};
	set<long> ** IDbacklog;

	IDbacklog = new set<long> * [sim.num_IDlogs];
	for (int i = 0; i < sim.num_IDlogs; i++)
		IDbacklog[i] = new set<long> [MAX_PCL_SPECIES];

	Field<Real> phi;
	Field<Real> source;
	Field<Real> chi;
	Field<Real> Sij;
	Field<Real> Bi;
	Field<Cplx> scalarFT;
	Field<Cplx> SijFT;
	Field<Cplx> BiFT;
	Field<Cplx> * zetaFT = NULL;
	source.initialize(lat,1);
	phi.initialize(lat,1);
	chi.initialize(lat,1);
	scalarFT.initialize(latFT,1);
	PlanFFT<Cplx> plan_source(&source, &scalarFT);
	PlanFFT<Cplx> plan_phi(&phi, &scalarFT);
	PlanFFT<Cplx> plan_chi(&chi, &scalarFT);
	Sij.initialize(lat,3,3,symmetric);
	SijFT.initialize(latFT,3,3,symmetric);
	PlanFFT<Cplx> plan_Sij(&Sij, &SijFT);
	Bi.initialize(lat,3);
	BiFT.initialize(latFT,3);
	PlanFFT<Cplx> plan_Bi(&Bi, &BiFT);
#ifdef CHECK_B
	Field<Real> Bi_check;
	Field<Cplx> BiFT_check;
	Bi_check.initialize(lat,3);
	BiFT_check.initialize(latFT,3);
	PlanFFT<Cplx> plan_Bi_check(&Bi_check, &BiFT_check);
#endif
#ifdef VELOCITY
	Field<Real> vi;
	Field<Cplx> viFT;
	vi.initialize(lat,3);
	viFT.initialize(latFT,3);
	PlanFFT<Cplx> plan_vi(&vi, &viFT);
	double a_old;
#endif
#ifdef TENSOR_EVOLUTION
	Field<Cplx> hijFT;
	Field<Cplx> hijprimeFT;
	hijFT.initialize(latFT,3,3,symmetric);
	hijprimeFT.initialize(latFT,3,3,symmetric);
	PlanFFT<Cplx> plan_hij(&Sij, &hijFT);
	hijprimeFT.alloc();
#endif

	update_cdm_fields[0] = &phi;
	update_cdm_fields[1] = &chi;
	update_cdm_fields[2] = &Bi;
	
	update_b_fields[0] = &phi;
	update_b_fields[1] = &chi;
	update_b_fields[2] = &Bi;
	
	update_ncdm_fields[0] = &phi;
	update_ncdm_fields[1] = &chi;
	update_ncdm_fields[2] = &Bi;

	project_Tij_fields[0] = &Sij;
	project_Tij_fields[1] = &phi;

	project_T0i_fields[0] = &Bi;
	project_T0i_fields[1] = &phi;
	
	Site x(lat);
	rKSite kFT(latFT);
	
	dx = 1.0 / (double) sim.numpts;
	numpts3d = (long) sim.numpts * (long) sim.numpts * (long) sim.numpts;
	
	for (int i = 0; i < 3; i++) // particles may never move farther than to the adjacent domain
	{
		if (lat.sizeLocal(i)-1 < sim.movelimit)
			sim.movelimit = lat.sizeLocal(i)-1;
	}
	parallel.min(sim.movelimit);

	fourpiG = 1.5 * sim.boxsize * sim.boxsize / C_SPEED_OF_LIGHT / C_SPEED_OF_LIGHT;
	a = 1. / (1. + sim.z_in);
	tau = -1;
	dtau = -1;
	dtau_old = -1;

	nvtxRangePushA("IC generation");
	
	if (ic.generator == ICGEN_BASIC)
		generateIC_basic(sim, ic, cosmo, fourpiG, &pcls_cdm, &pcls_b, pcls_ncdm, maxvel, &phi, &chi, &Bi, &source, &Sij, &scalarFT, &BiFT, &SijFT, &plan_phi, &plan_chi, &plan_Bi, &plan_source, &plan_Sij, 
#ifdef HAVE_CLASS
		class_background, class_perturbs,
#endif		
		params, numparam); // generates ICs on the fly
	else if (ic.generator == ICGEN_READ_FROM_DISK)
		readIC(sim, ic, cosmo, fourpiG, a, tau, dtau, dtau_old, &pcls_cdm, &pcls_b, pcls_ncdm, maxvel, &phi, &chi, &Bi, &source, &Sij, zetaFT, &scalarFT, &BiFT, &SijFT, &plan_phi, &plan_chi, &plan_Bi, &plan_source, &plan_Sij, cycle, snapcount, pkcount, restartcount, IDbacklog);
#ifdef ICGEN_RELIC
	else if (ic.generator == ICGEN_RELIC)
		generateIC_relic(sim, ic, cosmo, fourpiG, &pcls_cdm, &pcls_b, pcls_ncdm, maxvel, &phi, &chi, &Bi, &source, &Sij, zetaFT, &scalarFT, &BiFT, &SijFT, &plan_phi, &plan_chi, &plan_Bi, &plan_source, &plan_Sij, params, numparam);
#endif
#ifdef ICGEN_PREVOLUTION
	else if (ic.generator == ICGEN_PREVOLUTION)
		generateIC_prevolution(sim, ic, cosmo, fourpiG, a, tau, dtau, dtau_old, &pcls_cdm, &pcls_b, pcls_ncdm, maxvel, &phi, &chi, &Bi, &source, &Sij, &scalarFT, &BiFT, &SijFT, &plan_phi, &plan_chi, &plan_Bi, &plan_source, &plan_Sij, params, numparam);
#endif
#ifdef ICGEN_FALCONIC
	else if (ic.generator == ICGEN_FALCONIC)
		maxvel[0] = generateIC_FalconIC(sim, ic, cosmo, fourpiG, dtau, &pcls_cdm, pcls_ncdm, maxvel+1, &phi, &source, &chi, &Bi, &source, &Sij, &scalarFT, &BiFT, &SijFT, &plan_phi, &plan_source, &plan_chi, &plan_Bi, &plan_source, &plan_Sij);
#endif
	else
	{
		COUT << " error: IC generator not implemented!" << endl;
		parallel.abortForce();
	}

	nvtxRangePop();
	
	if (sim.baryon_flag > 1)
	{
		COUT << " error: baryon_flag > 1 after IC generation, something went wrong in IC generator!" << endl;
		parallel.abortForce();
	}
	
	numspecies = 1 + sim.baryon_flag + cosmo.num_ncdm;	
	parallel.max<double>(maxvel, numspecies);
	
	if (sim.gr_flag > 0)
	{
		for (int i = 0; i < numspecies; i++)
			maxvel[i] /= sqrt(maxvel[i] * maxvel[i] + 1.0);
	}

#ifdef CHECK_B
	if (sim.vector_flag == VECTOR_ELLIPTIC)
	{
		for (kFT.first(); kFT.test(); kFT.next())
		{
			BiFT_check(kFT, 0) = BiFT(kFT, 0);
			BiFT_check(kFT, 1) = BiFT(kFT, 1);
			BiFT_check(kFT, 2) = BiFT(kFT, 2);
		}
	}
#endif
#ifdef VELOCITY
	a_old = a;
	//projection_init(&vi);
	thrust::fill_n(thrust::device, vi.data(), 3*lat.sitesLocalGross(), Real(0));
#endif
#ifdef TENSOR_EVOLUTION
	/*for (kFT.first(); kFT.test(); kFT.next())
	{
		for (int i = 0; i < hijprimeFT.components(); i++)
			hijprimeFT(kFT, i) = Cplx(0,0);
	}*/
	#pragma omp parallel for
	for (long i = 0; i < hijprimeFT.components() * latFT.sitesLocalGross(); i++)
	{
		hijprimeFT.data()[i] = Cplx(0,0);
	}
#endif
	
#ifdef BENCHMARK
	initialization_time = MPI_Wtime() - start_time;
	parallel.sum(initialization_time);
	COUT << COLORTEXT_GREEN << " initialization complete." << COLORTEXT_RESET << " BENCHMARK: " << hourMinSec(initialization_time) << endl << endl;
#else
	COUT << COLORTEXT_GREEN << " initialization complete." << COLORTEXT_RESET << endl << endl;
#endif

#ifdef HAVE_CLASS
	if (sim.radiation_flag > 0 || sim.fluid_flag > 0)
	{
		cosmology cosmo2 = cosmo;
		if (cosmo.Hspline == NULL)
		{
			initializeCLASSstructures(sim, ic, cosmo, class_background, class_perturbs, params, numparam);
			loadBGFunctions(class_background, cosmo.Hspline, "H [1/Mpc]", sim.z_in, sim.boxsize/cosmo.h);
			cosmo.acc_H = gsl_interp_accel_alloc();
		}
		else
			cosmo2.Hspline = NULL;
		loadBGFunctions(class_background, cosmo.tauspline, "conf. time [Mpc]", sim.z_in, cosmo.h/sim.boxsize);
		cosmo.acc_tau = gsl_interp_accel_alloc();
		COUT << "Initial Hubble rate = " << Hconf(a, fourpiG, cosmo2) << " (gevolution), " << Hconf(a, fourpiG, cosmo) << " (CLASS) -- using CLASS" << endl;
		if ((
#ifdef ICGEN_RELIC
			ic.generator == ICGEN_RELIC || 
#endif
			ic.generator == ICGEN_READ_FROM_DISK) && zetaFT != NULL)  // zetaFT contains phi(k) at this point, so we need to divide out the transfer function
		{
			gsl_spline * tk1 = NULL;
			gsl_spline * tk2 = NULL;
			gsl_interp_accel * acc;
			loadTransferFunctions(class_background, class_perturbs, tk1, tk2, NULL, sim.boxsize, (1. / a) - 1., cosmo.h);

			#pragma omp parallel default(shared) firstprivate(kFT) private(acc, tmp)
			{
				acc = gsl_interp_accel_alloc();
				#pragma omp for collapse(2)
				for (int i = 0; i < zetaFT->lattice().sizeLocal(1); i++)
				{
					for (int j = 0; j < zetaFT->lattice().sizeLocal(2); j++)
					{
						if (!kFT.setCoord(0, j + zetaFT->lattice().coordSkip()[0], i + zetaFT->lattice().coordSkip()[1]))
						{
							std::cerr << "proc#" << parallel.rank() << ": Error in setting um zeta! Could not set coordinates at k=(0, " << j + zetaFT->lattice().coordSkip()[0] << ", " << i + zetaFT->lattice().coordSkip()[1] << ")" << std::endl;
						}

						if (kFT.coord(1) < (sim.numpts/2) + 1)
							tmp = kFT.coord(1)*kFT.coord(1);
						else
							tmp = (sim.numpts-kFT.coord(1))*(sim.numpts-kFT.coord(1));
						if (kFT.coord(2) < (sim.numpts/2) + 1)
							tmp += kFT.coord(2)*kFT.coord(2);
						else
							tmp += (sim.numpts-kFT.coord(2))*(sim.numpts-kFT.coord(2));

						for (int z = 0; z < zetaFT->lattice().sizeLocal(0); z++)
						{
							double k2 = z*z + tmp;

							if (k2 > 0)
							{
								k2 = 2. * M_PI * sqrt(k2);
								(*zetaFT)(kFT) /= -gsl_spline_eval(tk1, k2, acc) * numpts3d * M_PI * sqrt(Pk_primordial(k2 * cosmo.h / sim.boxsize, ic) / k2) / k2;
							}
							else
								(*zetaFT)(kFT) = Cplx(0.,0.);

							kFT.next();
						}
					}
				}
				gsl_interp_accel_free(acc);
			}
			
			gsl_spline_free(tk1);
			gsl_spline_free(tk2);
		}
		if (sim.gr_flag > 0 && a < 1. / (sim.z_switch_linearchi + 1.) && (ic.generator == ICGEN_BASIC || (ic.generator == ICGEN_READ_FROM_DISK && cycle == 0)))
		{
			prepareFTchiLinear(class_background, class_perturbs, scalarFT, sim, ic, cosmo, fourpiG, a, 1., zetaFT);
			plan_source.execute(FFT_BACKWARD);
			//for (x.first(); x.test(); x.next())
			//	chi(x) += source(x);
			thrust::transform(thrust::device, chi.data(), chi.data() + lat.sitesLocalGross(), source.data(), chi.data(), thrust::plus<Real>());
			chi.updateHalo();
		}
	}
	else if (cosmo.Hspline != NULL)
	{
		gsl_spline_free(cosmo.Hspline);
		gsl_interp_accel_free(cosmo.acc_H);
		cosmo.Hspline = NULL;
		freeCLASSstructures(class_background, class_perturbs);
	}
	if (numparam > 0) free(params);
#endif

	if (tau < 0.)
		tau = particleHorizon(a, fourpiG, cosmo);
	
	if (dtau < 0.)
	{
		if (sim.Cf * dx < sim.steplimit / Hconf(a, fourpiG, cosmo))
			dtau = sim.Cf * dx;
		else
			dtau = sim.steplimit / Hconf(a, fourpiG, cosmo);
	}

	if (dtau_old < 0.)
		dtau_old = 0.;

	while (true)    // main loop
	{
#ifdef BENCHMARK		
		cycle_start_time = MPI_Wtime();
#endif
		// construct stress-energy tensor
		nvtxRangePushA("Construct T00");
		//projection_init(&source);
		thrust::fill_n(thrust::device, source.data(), lat.sitesLocalGross(), Real(0));
#ifdef HAVE_CLASS
		if (sim.radiation_flag > 0 || sim.fluid_flag > 0)
			projection_T00_project(class_background, class_perturbs, source, scalarFT, &plan_source, sim, ic, cosmo, fourpiG, a, 1., zetaFT);
#endif
		if (sim.gr_flag > 0)
		{
			projection_T00_project(&pcls_cdm, &source, a, &phi);
			if (sim.baryon_flag)
				projection_T00_project(&pcls_b, &source, a, &phi);
			
			tmp = 0;
			for (int i = 0; i < cosmo.num_ncdm; i++)
			{
				if (a >= 1. / (sim.z_switch_deltancdm[i] + 1.) && sim.numpcl[1+sim.baryon_flag+i] > 0)
					projection_T00_project(pcls_ncdm+i, &source, a, &phi);
				else if (sim.radiation_flag == 0 || (a >= 1. / (sim.z_switch_deltancdm[i] + 1.) && sim.numpcl[1+sim.baryon_flag+i] == 0))
				{
					//tmp = bg_ncdm(a, cosmo, i);
					//for(x.first(); x.test(); x.next())
					//	source(x) += tmp;

					tmp += bg_ncdm(a, cosmo, i);
				}
			}

			if (tmp > 0)
			{
				Field<Real> * fieldptr = &source;

				lattice_for_each<<<dim3(source.lattice().sizeLocal(1), source.lattice().sizeLocal(2)), 128>>>(lattice_add_functor(), sim.numpts, &fieldptr, 1, &tmp, nullptr, nullptr);

				cudaDeviceSynchronize();
			}
		}
		else
		{
			scalarProjectionCIC_project(&pcls_cdm, &source);
			if (sim.baryon_flag)
				scalarProjectionCIC_project(&pcls_b, &source);
			for (int i = 0; i < cosmo.num_ncdm; i++)
			{
				if (a >= 1. / (sim.z_switch_deltancdm[i] + 1.) && sim.numpcl[1+sim.baryon_flag+i] > 0)
					scalarProjectionCIC_project(pcls_ncdm+i, &source);
			}
		}
		projection_T00_comm(&source);
		nvtxRangePop();
		
#ifdef VELOCITY
		if ((sim.out_pk & MASK_VEL) || (sim.out_snapshot & MASK_VEL))
		{
			//projection_init(&Bi);
			thrust::fill_n(thrust::device, Bi.data(), 3*lat.sitesLocalGross(), Real(0));
            projection_Ti0_project(&pcls_cdm, &Bi, &phi, &chi);
            vertexProjectionCIC_comm(&Bi);
            compute_vi_rescaled(cosmo, &vi, &source, &Bi, a, a_old);
            a_old = a;
		}
#endif
		
		nvtxRangePushA("Zero Tij");
		//projection_init(&Sij);
		thrust::fill_n(thrust::device, Sij.data(), 6*lat.sitesLocalGross(), Real(0));
		nvtxRangePop();

/*#ifdef ANISOTROPIC_EXPANSION
		projection_Tij_project(&pcls_cdm, &Sij, a, &phi, 1., hij_hom);
#else
		projection_Tij_project(&pcls_cdm, &Sij, a, &phi);
#endif
		if (sim.baryon_flag)
#ifdef ANISOTROPIC_EXPANSION
			projection_Tij_project(&pcls_b, &Sij, a, &phi, 1., hij_hom);
#else
			projection_Tij_project(&pcls_b, &Sij, a, &phi);
#endif*/

		if (a >= 1. / (sim.z_switch_linearchi + 1.))
		{
			for (int i = 0; i < cosmo.num_ncdm; i++)
			{
				if (sim.numpcl[1+sim.baryon_flag+i] > 0)
				{
					nvtxRangePushA("Tij projection of ncdm particle species");
#ifdef ANISOTROPIC_EXPANSION
					projection_Tij_project(pcls_ncdm+i, &Sij, a, &phi, 1., hij_hom);
#else
					projection_Tij_project(pcls_ncdm+i, &Sij, a, &phi);
#endif
					nvtxRangePop();
				}
			}
		}
		//projection_Tij_comm(&Sij);
		
#ifdef BENCHMARK 
		projection_time += MPI_Wtime() - cycle_start_time;
		ref_time = MPI_Wtime();
#endif
		
		nvtxRangePushA("Solve phi");
		if (sim.gr_flag > 0)
		{
			if (dtau_old > 0.)
			{
				nvtxRangePushA("prepareFTsource");
				T00hom = prepareFTsource(phi, chi, source, cosmo.Omega_cdm + cosmo.Omega_b + bg_ncdm(a, cosmo), source, 3. * Hconf(a, fourpiG, cosmo) * dx * dx / dtau_old, fourpiG * dx * dx / a, 3. * Hconf(a, fourpiG, cosmo) * Hconf(a, fourpiG, cosmo) * dx * dx);  // prepare nonlinear source for phi update
				T00hom /= (double) numpts3d;
				nvtxRangePop();
			}
			
			if (cycle % CYCLE_INFO_INTERVAL == 0)
			{
				COUT << " cycle " << cycle << ", background information: z = " << (1./a) - 1. << ", average T00 = " << T00hom << ", background model = " << cosmo.Omega_cdm + cosmo.Omega_b + bg_ncdm(a, cosmo) << endl;
			}
		}

		if (sim.gr_flag == 0 || dtau_old > 0.)
		{
#ifdef BENCHMARK
			ref2_time= MPI_Wtime();
#endif
			nvtxRangePushA("FFT forward source");
			plan_source.execute(FFT_FORWARD);  // go to k-space
			nvtxRangePop();
#ifdef BENCHMARK
			fft_time += MPI_Wtime() - ref2_time;
			fft_count++;
#endif
		}

		if (sim.gr_flag > 0 || sim.vector_flag == VECTOR_PARABOLIC)
		{
			nvtxRangePushA("offload Tij projection to GPU");
			f_params[0] = a;
			f_params[1] = 1.;
			projection_Tij_project_Async(&pcls_cdm, project_Tij_fields, 2, f_params);
			if (sim.baryon_flag)
				projection_Tij_project_Async(&pcls_b, project_Tij_fields, 2, f_params);
			nvtxRangePop();
		}
		
		nvtxRangePushA("solveModifiedPoissonFT");
		if (sim.gr_flag == 0)
		{
			solveModifiedPoissonFT(scalarFT, scalarFT, fourpiG / a);  // Newton: phi update (k-space)
		}
		else if (dtau_old > 0.)
		{
			solveModifiedPoissonFT(scalarFT, scalarFT, 1. / (dx * dx), 3. * Hconf(a, fourpiG, cosmo) / dtau_old);  // phi update (k-space)
		}
		nvtxRangePop();

		if (sim.gr_flag > 0 || sim.vector_flag == VECTOR_PARABOLIC)
		{
			nvtxRangePushA("sync and finalize Tij projection");
			auto success = cudaDeviceSynchronize();

			if (success != cudaSuccess)
			{
				std::cerr << "CUDA kernel failed: " << cudaGetErrorString(success) << std::endl;
				throw std::runtime_error("Error in CUDA kernel called via projection_Tij_project_Async");
			}

			projection_Tij_comm(&Sij);
			nvtxRangePop();
		}

		if (sim.gr_flag == 0 || dtau_old > 0.)
		{		
#ifdef BENCHMARK
			ref2_time= MPI_Wtime();
#endif	
			nvtxRangePushA("FFT backward phi");	
			plan_phi.execute(FFT_BACKWARD);	 // go back to position space
			nvtxRangePop();
#ifdef BENCHMARK
			fft_time += MPI_Wtime() - ref2_time;
			fft_count++;
#endif	

			nvtxRangePushA("Update halo phi");
			phi.updateHalo();  // communicate halo values
			nvtxRangePop();
		}

		nvtxRangePop();

		if (kFT.setCoord(0, 0, 0))
			phi_hom = scalarFT(kFT).real();
		
		if (sim.gr_flag > 0 || sim.vector_flag == VECTOR_PARABOLIC
#ifdef CHECK_B
			|| true
#endif
#ifdef HAVE_CLASS
			|| (sim.radiation_flag > 0 && a < 1. / (sim.z_switch_linearchi + 1.))
#endif		
		)
		{
			nvtxRangePushA("Solve chi");
			nvtxRangePushA("prepareFTsource");
			prepareFTsource(phi, Sij, Sij, 2. * fourpiG * dx * dx / a);  // prepare nonlinear source for additional equations
			nvtxRangePop();

#ifdef BENCHMARK
			ref2_time= MPI_Wtime();
#endif		
			nvtxRangePushA("FFT forward Sij");
			plan_Sij.execute(FFT_FORWARD);  // go to k-space
			nvtxRangePop();
#ifdef BENCHMARK
			fft_time += MPI_Wtime() - ref2_time;
			fft_count += 6;
#endif

			if (sim.vector_flag == VECTOR_ELLIPTIC)
			{
				nvtxRangePushA("Zero T0i");
				//projection_init(&Bi);
				thrust::fill_n(thrust::device, Bi.data(), 3*lat.sitesLocalGross(), Real(0));
				nvtxRangePop();
				//projection_T0i_project(&pcls_cdm, &Bi, &phi);
				//if (sim.baryon_flag)
				//	projection_T0i_project(&pcls_b, &Bi, &phi);
				for (int i = 0; i < cosmo.num_ncdm; i++)
				{
					if (a >= 1. / (sim.z_switch_Bncdm[i] + 1.) && sim.numpcl[1+sim.baryon_flag+i] > 0)
					{
						nvtxRangePushA("T0i projection of ncdm particle species");
						projection_T0i_project(pcls_ncdm+i, &Bi, &phi);
						nvtxRangePop();
					}
				}
				//projection_T0i_comm(&Bi);
				nvtxRangePushA("offload T0i projection to GPU");
				f_params[0] = 1.;
				projection_T0i_project_Async(&pcls_cdm, project_T0i_fields, 2, f_params);
				if (sim.baryon_flag)
					projection_T0i_project_Async(&pcls_b, project_T0i_fields, 2, f_params);
				nvtxRangePop();
			}

			nvtxRangePushA("projectFTscalar");
#ifdef HAVE_CLASS
			if (sim.radiation_flag > 0 && a < 1. / (sim.z_switch_linearchi + 1.))
			{
				prepareFTchiLinear(class_background, class_perturbs, scalarFT, sim, ic, cosmo, fourpiG, a, 1., zetaFT);
				projectFTscalar(SijFT, scalarFT, 1);
			}
			else
#endif		
			projectFTscalar(SijFT, scalarFT);  // construct chi by scalar projection (k-space)
			nvtxRangePop();

			if (sim.vector_flag == VECTOR_ELLIPTIC)
			{
				nvtxRangePushA("sync and finalize T0i projection");
				auto success_T0i = cudaDeviceSynchronize();

				if (success_T0i != cudaSuccess)
				{
					std::cerr << "CUDA kernel failed: " << cudaGetErrorString(success_T0i) << std::endl;
					throw std::runtime_error("Error in CUDA kernel called via projection_T0i_project_Async");
				}

				projection_T0i_comm(&Bi);
				nvtxRangePop();
			}

#ifdef BENCHMARK
			ref2_time= MPI_Wtime();
#endif	
			nvtxRangePushA("FFT backward chi");
			plan_chi.execute(FFT_BACKWARD);	 // go back to position space
			nvtxRangePop();
#ifdef BENCHMARK
			fft_time += MPI_Wtime() - ref2_time;
			fft_count++;
#endif	
			nvtxRangePushA("Update halo chi");
			chi.updateHalo();  // communicate halo values
			nvtxRangePop();
			nvtxRangePop();
		}

		nvtxRangePushA("Solve B (k-space)");
		if (sim.vector_flag == VECTOR_ELLIPTIC
#ifndef CHECK_B
			&& sim.gr_flag > 0
#endif
		)
		{
#ifdef BENCHMARK
			ref2_time= MPI_Wtime();
#endif
			nvtxRangePushA("FFT forward T0i");
			plan_Bi.execute(FFT_FORWARD);
			nvtxRangePop();
#ifdef BENCHMARK
			fft_time += MPI_Wtime() - ref2_time;
			fft_count += 3;
#endif
			nvtxRangePushA("projectFTvector");
			projectFTvector(BiFT, BiFT, fourpiG * dx * dx); // solve B using elliptic constraint (k-space)
			nvtxRangePop();
#ifdef CHECK_B
			nvtxRangePushA("evolveFTvector (check)");
			evolveFTvector(SijFT, BiFT_check, a * a * dtau_old);
			nvtxRangePop();
#endif
		}
		else if (sim.vector_flag == VECTOR_PARABOLIC)
		{
			nvtxRangePushA("evolveFTvector");
			evolveFTvector(SijFT, BiFT, a * a * dtau_old);  // evolve B using vector projection (k-space)
			nvtxRangePop();
		}
		nvtxRangePop();

		if (sim.gr_flag > 0)
		{
			nvtxRangePushA("Solve B (position space)");
#ifdef BENCHMARK
			ref2_time= MPI_Wtime();
#endif		
			nvtxRangePushA("FFT backward B");	
			plan_Bi.execute(FFT_BACKWARD);  // go back to position space
			nvtxRangePop();
#ifdef BENCHMARK
			fft_time += MPI_Wtime() - ref2_time;
			fft_count += 3;
#endif
			nvtxRangePushA("Update halo B");
			Bi.updateHalo();  // communicate halo values
			nvtxRangePop();
			nvtxRangePop();

#ifdef TENSOR_EVOLUTION
			nvtxRangePushA("Solve hij (k-space)");
			if (cycle == 0)
				projectFTtensor(SijFT, hijFT);
			else
				evolveFTtensor(SijFT, hijFT, hijprimeFT, Hconf(a, fourpiG, cosmo), dtau, dtau_old);
			nvtxRangePop();
#endif

#ifdef ANISOTROPIC_EXPANSION
			if (kFT.setCoord(0, 0, 0))
			{
#ifdef TENSOR_EVOLUTION
				hij_hom[0] = hijFT(kFT, 0, 0).real();
				hij_hom[1] = hijFT(kFT, 0, 1).real();
				hij_hom[2] = hijFT(kFT, 0, 2).real();
				hij_hom[3] = hijFT(kFT, 1, 1).real();
				hij_hom[4] = hijFT(kFT, 1, 2).real();

				hijprime_hom[0] = hijprimeFT(kFT, 0, 0).real();
				hijprime_hom[1] = hijprimeFT(kFT, 0, 1).real();
				hijprime_hom[2] = hijprimeFT(kFT, 0, 2).real();
				hijprime_hom[3] = hijprimeFT(kFT, 1, 1).real();
				hijprime_hom[4] = hijprimeFT(kFT, 1, 2).real();
#else
				for (int i = 0; i < 5; i++)
					hij_hom[i] += hijprime_hom[i] * dtau_old;
				
				hijprime_hom[0] = ((1. - 0.5 * (dtau_old + dtau) * Hconf(a, fourpiG, cosmo)) * hijprime_hom[0] + (dtau_old + dtau) * (Real(2) * SijFT(kFT, 0, 0).real() - SijFT(kFT, 1, 1).real() - SijFT(kFT, 2, 2).real()) / Real(3) / sim.numpts) / (1. + 0.5 * (dtau_old + dtau) * Hconf(a, fourpiG, cosmo));
				hijprime_hom[1] = ((1. - 0.5 * (dtau_old + dtau) * Hconf(a, fourpiG, cosmo)) * hijprime_hom[1] + (dtau_old + dtau) * SijFT(kFT, 0, 1).real() / sim.numpts) / (1. + 0.5 * (dtau_old + dtau) * Hconf(a, fourpiG, cosmo));
				hijprime_hom[2] = ((1. - 0.5 * (dtau_old + dtau) * Hconf(a, fourpiG, cosmo)) * hijprime_hom[2] + (dtau_old + dtau) * SijFT(kFT, 0, 2).real() / sim.numpts) / (1. + 0.5 * (dtau_old + dtau) * Hconf(a, fourpiG, cosmo));
				hijprime_hom[3] = ((1. - 0.5 * (dtau_old + dtau) * Hconf(a, fourpiG, cosmo)) * hijprime_hom[3] + (dtau_old + dtau) * (Real(2) * SijFT(kFT, 1, 1).real() - SijFT(kFT, 0, 0).real() - SijFT(kFT, 2, 2).real()) / Real(3) / sim.numpts) / (1. + 0.5 * (dtau_old + dtau) * Hconf(a, fourpiG, cosmo));
				hijprime_hom[4] = ((1. - 0.5 * (dtau_old + dtau) * Hconf(a, fourpiG, cosmo)) * hijprime_hom[4] + (dtau_old + dtau) * SijFT(kFT, 1, 2).real() / sim.numpts) / (1. + 0.5 * (dtau_old + dtau) * Hconf(a, fourpiG, cosmo));
#endif
			}
			
			parallel.broadcast(hij_hom, 5, 0);
			parallel.broadcast(hijprime_hom, 5, 0);

			// anisotropic expansion parameters for particle updates
			f_params[2] = hij_hom[0];
			f_params[3] = hij_hom[1];
			f_params[4] = hij_hom[2];
			f_params[5] = hij_hom[3];
			f_params[6] = hij_hom[4];
#endif
		}

#ifdef BENCHMARK 
		gravity_solver_time += MPI_Wtime() - ref_time;
		ref_time = MPI_Wtime();
#endif

		// record some background data
		if (kFT.setCoord(0, 0, 0))
		{
			sprintf(filename, "%s%s_background.dat", sim.output_path, sim.basename_generic);
			outfile = fopen(filename, "a");
			if (outfile == NULL)
			{
				cout << " error opening file for background output!" << endl;
			}
			else
			{
#ifdef ANISOTROPIC_EXPANSION
				if (cycle == 0)
					fprintf(outfile, "# background statistics\n# cycle   tau/boxsize    a             conformal H/H0  phi(k=0)       T00(k=0)       h00(k=0)       h01(k=0)       h02(k=0)       h11(k=0)       h12(k=0)\n");
				fprintf(outfile, " %6d   %e   %e   %e   %e   %e   %e   %e   %e   %e   %e\n", cycle, tau, a, Hconf(a, fourpiG, cosmo) / Hconf(1., fourpiG, cosmo), phi_hom, T00hom, hij_hom[0], hij_hom[1], hij_hom[2], hij_hom[3], hij_hom[4]);
#else
				if (cycle == 0)
					fprintf(outfile, "# background statistics\n# cycle   tau/boxsize    a             conformal H/H0  phi(k=0)       T00(k=0)\n");
				fprintf(outfile, " %6d   %e   %e   %e   %e   %e\n", cycle, tau, a, Hconf(a, fourpiG, cosmo) / Hconf(1., fourpiG, cosmo), phi_hom, T00hom);
#endif
				fclose(outfile);
			}
		}
		// done recording background data

		// lightcone output
		nvtxRangePushA("Lightcone output");
		if (sim.num_lightcone > 0)
			writeLightcones(sim, cosmo, fourpiG, a, tau, dtau, dtau_old, maxvel[0], cycle, h5filename + sim.basename_lightcone, &pcls_cdm, &pcls_b, pcls_ncdm, &phi, &chi, &Bi, &Sij, &BiFT, &SijFT, &plan_Bi, &plan_Sij, done_hij, IDbacklog);
		else done_hij = 0;
		nvtxRangePop();

#ifdef BENCHMARK
		lightcone_output_time += MPI_Wtime() - ref_time;
		ref_time = MPI_Wtime();
#endif 

		// snapshot output
		if (snapcount < sim.num_snapshot && 1. / a < sim.z_snapshot[snapcount] + 1.)
		{
			nvtxRangePushA("Snapshot output");
			COUT << COLORTEXT_CYAN << " writing snapshot" << COLORTEXT_RESET << " at z = " << ((1./a) - 1.) <<  " (cycle " << cycle << "), tau/boxsize = " << tau << endl;

			writeSnapshots(sim, cosmo, fourpiG, a, dtau_old, done_hij, snapcount, h5filename + sim.basename_snapshot, &pcls_cdm, &pcls_b, pcls_ncdm, &phi, &chi, &Bi, &source, &Sij, &scalarFT, &BiFT, &SijFT, &plan_phi, &plan_chi, &plan_Bi, &plan_source, &plan_Sij
#ifdef CHECK_B
				, &Bi_check, &BiFT_check, &plan_Bi_check
#endif
#ifdef VELOCITY
				, &vi
#endif
			);

			snapcount++;
			nvtxRangePop();
		}
		
#ifdef BENCHMARK
		snapshot_output_time += MPI_Wtime() - ref_time;
		ref_time = MPI_Wtime();
#endif
		
		// power spectra
		if (pkcount < sim.num_pk && 1. / a < sim.z_pk[pkcount] + 1.)
		{
			nvtxRangePushA("Power spectrum output");
			COUT << COLORTEXT_CYAN << " writing power spectra" << COLORTEXT_RESET << " at z = " << ((1./a) - 1.) <<  " (cycle " << cycle << "), tau/boxsize = " << tau << endl;

			writeSpectra(sim, cosmo, fourpiG, a, pkcount,
#ifdef HAVE_CLASS
				class_background, class_perturbs, ic,
#endif
				&pcls_cdm, &pcls_b, pcls_ncdm, &phi, &chi, &Bi, &source, &Sij, zetaFT, &scalarFT, &BiFT, &SijFT, &plan_phi, &plan_chi, &plan_Bi, &plan_source, &plan_Sij
#ifdef CHECK_B
				, &Bi_check, &BiFT_check, &plan_Bi_check
#endif
#ifdef VELOCITY
				, &vi, &viFT, &plan_vi
#endif
#ifdef TENSOR_EVOLUTION
				, &hijFT, &hijprimeFT
#endif
			);

			pkcount++;
			nvtxRangePop();
		}

#ifdef EXACT_OUTPUT_REDSHIFTS
		tmp = a;
		rungekutta4bg(tmp, fourpiG, cosmo, 0.5 * dtau);
		rungekutta4bg(tmp, fourpiG, cosmo, 0.5 * dtau);

		if (pkcount < sim.num_pk && 1. / tmp < sim.z_pk[pkcount] + 1.)
		{
			nvtxRangePushA("Power spectrum output (exact redshifts)");
			writeSpectra(sim, cosmo, fourpiG, a, pkcount,
#ifdef HAVE_CLASS
				class_background, class_perturbs, ic,
#endif
				&pcls_cdm, &pcls_b, pcls_ncdm, &phi, &chi, &Bi, &source, &Sij, zetaFT, &scalarFT, &BiFT, &SijFT, &plan_phi, &plan_chi, &plan_Bi, &plan_source, &plan_Sij
#ifdef CHECK_B
				, &Bi_check, &BiFT_check, &plan_Bi_check
#endif
#ifdef VELOCITY
				, &vi, &viFT, &plan_vi
#endif
#ifdef TENSOR_EVOLUTION
				, &hijFT, &hijprimeFT
#endif
			);
			nvtxRangePop();
		}
#endif // EXACT_OUTPUT_REDSHIFTS
		
#ifdef BENCHMARK
		spectra_output_time += MPI_Wtime() - ref_time;
#endif

		if (pkcount >= sim.num_pk && snapcount >= sim.num_snapshot)
		{
			int i;
			for (i = 0; i < sim.num_lightcone; i++)
			{
				if (sim.lightcone[i].z + 1. < 1. / a)
					i = sim.num_lightcone + 1;
			}
			if (i == sim.num_lightcone) break; // simulation complete
		}
		
		// compute number of step subdivisions for ncdm particle updates
		for (int i = 0; i < cosmo.num_ncdm; i++)
		{
			if (dtau * maxvel[i+1+sim.baryon_flag] > dx * sim.movelimit)
				numsteps_ncdm[i] = (int) ceil(dtau * maxvel[i+1+sim.baryon_flag] / dx / sim.movelimit);
			else numsteps_ncdm[i] = 1;
		}
		
		if (cycle % CYCLE_INFO_INTERVAL == 0)
		{
			COUT << " cycle " << cycle << ", time integration information: max |v| = " << maxvel[0] << " (cdm Courant factor = " << maxvel[0] * dtau / dx;
			if (sim.baryon_flag)
			{
				COUT << "), baryon max |v| = " << maxvel[1] << " (Courant factor = " << maxvel[1] * dtau / dx;
			}
			
			COUT << "), time step / Hubble time = " << Hconf(a, fourpiG, cosmo) * dtau;
			
			for (int i = 0; i < cosmo.num_ncdm; i++)
			{
				if (i == 0)
				{
					COUT << endl << " time step subdivision for ncdm species: ";
				}
				COUT << numsteps_ncdm[i] << " (max |v| = " << maxvel[i+1+sim.baryon_flag] << ")";
				if (i < cosmo.num_ncdm-1)
				{
					COUT << ", ";
				}
			}
			
			COUT << endl;
		}

		nvtxRangePushA("Particle update: ncdm species");
#ifdef BENCHMARK
		ref2_time = MPI_Wtime();
#endif
		for (int i = 0; i < cosmo.num_ncdm; i++) // non-cold DM particle update
		{
			if (sim.numpcl[1+sim.baryon_flag+i] == 0) continue;
			
			tmp = a;
			
			for (int j = 0; j < numsteps_ncdm[i]; j++)
			{
				f_params[0] = tmp;
				f_params[1] = tmp * tmp * sim.numpts;
				if (sim.gr_flag > 0)
					maxvel[i+1+sim.baryon_flag] = pcls_ncdm[i].updateVel(update_q, (dtau + dtau_old) / 2. / numsteps_ncdm[i], update_ncdm_fields, (1. / a < ic.z_relax + 1. ? 3 : 2), f_params);
				else
					maxvel[i+1+sim.baryon_flag] = pcls_ncdm[i].updateVel(update_q_Newton, (dtau + dtau_old) / 2. / numsteps_ncdm[i], update_ncdm_fields, ((sim.radiation_flag + sim.fluid_flag > 0 && a < 1. / (sim.z_switch_linearchi + 1.)) ? 2 : 1), f_params);

#ifdef BENCHMARK
				update_q_count++;
				update_q_time += MPI_Wtime() - ref2_time;
				ref2_time = MPI_Wtime();
#endif

				rungekutta4bg(tmp, fourpiG, cosmo, 0.5 * dtau / numsteps_ncdm[i]);
				f_params[0] = tmp;
				f_params[1] = tmp * tmp * sim.numpts;
				
				if (sim.gr_flag > 0)
					pcls_ncdm[i].moveParticles(update_pos, dtau / numsteps_ncdm[i], update_ncdm_fields, (1. / a < ic.z_relax + 1. ? 3 : 2), f_params);
				else
					pcls_ncdm[i].moveParticles(update_pos_Newton, dtau / numsteps_ncdm[i], NULL, 0, f_params);
#ifdef BENCHMARK
				moveParts_count++;
				moveParts_time += MPI_Wtime() - ref2_time;
				ref2_time = MPI_Wtime();
#endif
				rungekutta4bg(tmp, fourpiG, cosmo, 0.5 * dtau / numsteps_ncdm[i]);
			}
		}
		nvtxRangePop();

		// cdm and baryon particle update
		nvtxRangePushA("Particle update: cdm and baryons, kick step");
		f_params[0] = a;
		f_params[1] = a * a * sim.numpts;
		if (sim.gr_flag > 0)
		{
			maxvel[0] = pcls_cdm.updateVel(update_q_functor(), (dtau + dtau_old) / 2., update_cdm_fields, (1. / a < ic.z_relax + 1. ? 3 : 2), f_params);
			if (sim.baryon_flag)
				maxvel[1] = pcls_b.updateVel(update_q_functor(), (dtau + dtau_old) / 2., update_b_fields, (1. / a < ic.z_relax + 1. ? 3 : 2), f_params);
		}
		else
		{
			maxvel[0] = pcls_cdm.updateVel(update_q_Newton_functor(), (dtau + dtau_old) / 2., update_cdm_fields, ((sim.radiation_flag + sim.fluid_flag > 0 && a < 1. / (sim.z_switch_linearchi + 1.)) ? 2 : 1), f_params);
			if (sim.baryon_flag)
				maxvel[1] = pcls_b.updateVel(update_q_Newton_functor(), (dtau + dtau_old) / 2., update_b_fields, ((sim.radiation_flag + sim.fluid_flag > 0 && a < 1. / (sim.z_switch_linearchi + 1.)) ? 2 : 1), f_params);
		}
		nvtxRangePop();

#ifdef BENCHMARK
		update_q_count++;
		update_q_time += MPI_Wtime() - ref2_time;
		ref2_time = MPI_Wtime();
#endif
				
		rungekutta4bg(a, fourpiG, cosmo, 0.5 * dtau);  // evolve background by half a time step

		nvtxRangePushA("Particle update: cdm and baryons, drift step");
		f_params[0] = a;
		f_params[1] = a * a * sim.numpts;
		if (sim.gr_flag > 0)
		{
			pcls_cdm.moveParticles(update_pos_functor(), dtau, update_cdm_fields, (1. / a < ic.z_relax + 1. ? 3 : 0), f_params);
			if (sim.baryon_flag)
				pcls_b.moveParticles(update_pos_functor(), dtau, update_b_fields, (1. / a < ic.z_relax + 1. ? 3 : 0), f_params);
		}
		else
		{
			pcls_cdm.moveParticles(update_pos_Newton_functor(), dtau, NULL, 0, f_params);
			if (sim.baryon_flag)
				pcls_b.moveParticles(update_pos_Newton_functor(), dtau, NULL, 0, f_params);
		}
		nvtxRangePop();

#ifdef BENCHMARK
		moveParts_count++;
		moveParts_time += MPI_Wtime() - ref2_time;
#endif

		rungekutta4bg(a, fourpiG, cosmo, 0.5 * dtau);  // evolve background by half a time step
		
		parallel.max<double>(maxvel, numspecies);
		
		if (sim.gr_flag > 0)
		{
			for (int i = 0; i < numspecies; i++)
				maxvel[i] /= sqrt(maxvel[i] * maxvel[i] + 1.0);
		}
		// done particle update
		
		tau += dtau;
		
		if (sim.wallclocklimit > 0.)   // check for wallclock time limit
		{
			tmp = MPI_Wtime() - start_time;
			parallel.max(tmp);
			if (tmp > sim.wallclocklimit)   // hibernate
			{
				COUT << COLORTEXT_YELLOW << " reaching hibernation wallclock limit, hibernating..." << COLORTEXT_RESET << endl;
				COUT << COLORTEXT_CYAN << " writing hibernation point" << COLORTEXT_RESET << " at z = " << ((1./a) - 1.) <<  " (cycle " << cycle << "), tau/boxsize = " << tau << endl;
				if (sim.vector_flag == VECTOR_PARABOLIC && sim.gr_flag == 0)
					plan_Bi.execute(FFT_BACKWARD);
#ifdef CHECK_B
				if (sim.vector_flag == VECTOR_ELLIPTIC)
				{
					plan_Bi_check.execute(FFT_BACKWARD);
					//hibernate(sim, ic, cosmo, &pcls_cdm, &pcls_b, pcls_ncdm, phi, chi, Bi_check, a, tau, dtau, cycle); // FIXME
				}
				else
#endif
				//hibernate(sim, ic, cosmo, &pcls_cdm, &pcls_b, pcls_ncdm, phi, chi, Bi, a, tau, dtau, cycle); // FIXME
				break;
			}
		}
		
		if (restartcount < sim.num_restart && 1. / a < sim.z_restart[restartcount] + 1.)
		{
			COUT << COLORTEXT_CYAN << " writing hibernation point" << COLORTEXT_RESET << " at z = " << ((1./a) - 1.) <<  " (cycle " << cycle << "), tau/boxsize = " << tau << endl;
			if (sim.vector_flag == VECTOR_PARABOLIC && sim.gr_flag == 0)
				plan_Bi.execute(FFT_BACKWARD);
#ifdef CHECK_B
			if (sim.vector_flag == VECTOR_ELLIPTIC)
			{
				plan_Bi_check.execute(FFT_BACKWARD);
				//hibernate(sim, ic, cosmo, &pcls_cdm, &pcls_b, pcls_ncdm, phi, chi, Bi_check, a, tau, dtau, cycle, restartcount);  // FIXME
			}
			else
#endif
			//hibernate(sim, ic, cosmo, &pcls_cdm, &pcls_b, pcls_ncdm, phi, chi, Bi, a, tau, dtau, cycle, restartcount);  // FIXME
			restartcount++;
		}
		
		dtau_old = dtau;
		
		if (sim.Cf * dx < sim.steplimit / Hconf(a, fourpiG, cosmo))
			dtau = sim.Cf * dx;
		else
			dtau = sim.steplimit / Hconf(a, fourpiG, cosmo);
		   
		cycle++;
		
#ifdef BENCHMARK
		cycle_time += MPI_Wtime()-cycle_start_time;
#endif
	}
	
	COUT << COLORTEXT_GREEN << " simulation complete." << COLORTEXT_RESET << endl;

#ifdef BENCHMARK
		ref_time = MPI_Wtime();
#endif

if (zetaFT != NULL)
	delete[] zetaFT;

for (int i = 0; i < sim.num_IDlogs; i++)
{
	if (IDbacklog[i] != NULL)
		delete[] IDbacklog[i];
}
delete [] IDbacklog;

#ifdef HAVE_CLASS
	if (sim.radiation_flag > 0 || sim.fluid_flag > 0)
		freeCLASSstructures(class_background, class_perturbs);
#endif

#ifdef BENCHMARK
	lightcone_output_time += MPI_Wtime() - ref_time;
	run_time = MPI_Wtime() - start_time;

	parallel.sum(run_time);
	parallel.sum(cycle_time);
	parallel.sum(projection_time);
	parallel.sum(snapshot_output_time);
	parallel.sum(spectra_output_time);
	parallel.sum(lightcone_output_time);
	parallel.sum(gravity_solver_time);
	parallel.sum(fft_time);
	parallel.sum(update_q_time);
	parallel.sum(moveParts_time);
	
	COUT << endl << "BENCHMARK" << endl;   
	COUT << "total execution time  : "<<hourMinSec(run_time) << endl;
	COUT << "total number of cycles: "<< cycle << endl;
	COUT << "time consumption breakdown:" << endl;
	COUT << "initialization   : "  << hourMinSec(initialization_time) << " ; " << 100. * initialization_time/run_time <<"%."<<endl;
	COUT << "main loop        : "  << hourMinSec(cycle_time) << " ; " << 100. * cycle_time/run_time <<"%."<<endl;
	
	COUT << "----------- main loop: components -----------"<<endl;
	COUT << "projections                : "<< hourMinSec(projection_time) << " ; " << 100. * projection_time/cycle_time <<"%."<<endl;
	COUT << "snapshot outputs           : "<< hourMinSec(snapshot_output_time) << " ; " << 100. * snapshot_output_time/cycle_time <<"%."<<endl;
	COUT << "lightcone outputs          : "<< hourMinSec(lightcone_output_time) << " ; " << 100. * lightcone_output_time/cycle_time <<"%."<<endl;
	COUT << "power spectra outputs      : "<< hourMinSec(spectra_output_time) << " ; " << 100. * spectra_output_time/cycle_time <<"%."<<endl;
	COUT << "update momenta (count: "<<update_q_count <<"): "<< hourMinSec(update_q_time) << " ; " << 100. * update_q_time/cycle_time <<"%."<<endl;
	COUT << "move particles (count: "<< moveParts_count <<"): "<< hourMinSec(moveParts_time) << " ; " << 100. * moveParts_time/cycle_time <<"%."<<endl;
	COUT << "gravity solver             : "<< hourMinSec(gravity_solver_time) << " ; " << 100. * gravity_solver_time/cycle_time <<"%."<<endl;
	COUT << "-- thereof Fast Fourier Transforms (count: " << fft_count <<"): "<< hourMinSec(fft_time) << " ; " << 100. * fft_time/gravity_solver_time <<"%."<<endl;
#endif

#ifdef EXTERNAL_IO	
		ioserver.stop();
	}
#endif

	if (cosmo.num_ncdm > 0) delete[] pcls_ncdm;

	parallel.finalize();

	return 0;
}


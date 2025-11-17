/*
 * Copyright (C) NHR@FAU, University Erlangen-Nuremberg.
 * All rights reserved. This file is part of nusif-solver.
 * Use of this source code is governed by a MIT style
 * license that can be found in the LICENSE file.
 */
#include "math.h"
#include "stdio.h"
#include "stdlib.h"

#include "allocate.h"
#include "parameter.h"
#include "solver.h"
#include<mpi.h>

#define PI        3.14159265358979323846
#define P(i, j)   p[(j) * (imax + 2) + (i)]
#define RHS(i, j) rhs[(j) * (imax + 2) + (i)]

//change this to 1 for RED black sor solver or set in compilation step
#define RED_BLACK_SOLVER 0

static int sizeOfRank(int rank, int size, int N)
{
    return N/size + ((N%size)>rank ? 1 : 0);
}

static void exchange(Solver* solver)
{
    MPI_Request requests[4] = { MPI_REQUEST_NULL,
        MPI_REQUEST_NULL,
        MPI_REQUEST_NULL,
        MPI_REQUEST_NULL };

    /* exchange ghost cells with top neighbor */
    if (solver->rank + 1 < solver->size) {
        int top     = solver->rank+1;

        double* src = solver->p;
        double* dst = solver->p;

        //the send we will send from the actual row
        MPI_Isend(&src[(solver->jmaxLocal)*(solver->imax+2)+1],solver->imax,MPI_DOUBLE,top,1,MPI_COMM_WORLD,&requests[0]);
        //the recv we will recv into the halo row 
        MPI_Irecv(&dst[(solver->jmaxLocal+1)*(solver->imax+2)+1],solver->imax,MPI_DOUBLE,top,2,MPI_COMM_WORLD,&requests[1]);
    }

    /* exchange ghost cells with bottom neighbor */
    if (solver->rank > 0) {
        int bottom  = solver->rank-1;
        double* src = solver->p;
        double* dst = solver->p;

        //for top as the send is 1 and recv is 2 for bottom it should be 2 and 1 
        MPI_Isend(&src[((solver->imax+2)+1)],solver->imax,MPI_DOUBLE,bottom,2,MPI_COMM_WORLD,&requests[2]);
        MPI_Irecv(&dst[1],solver->imax,MPI_DOUBLE,bottom,1,MPI_COMM_WORLD,&requests[3]);
    }

    MPI_Waitall(4, requests, MPI_STATUSES_IGNORE);
}

void getResult(Solver* solver)
{
    double* p = NULL;
    int *rcvCounts, *displs;

    if (solver->rank == 0) {
        p = allocate(64, (solver->imax + 2) * (solver->jmax + 2) * sizeof(double));
        rcvCounts    = allocate(64, (solver->size) * sizeof(int));
        displs       = allocate(64, (solver->size) * sizeof(int));
        // rcvCounts[0] = (solver->jmaxLocal+1)*(solver->imax+2);
        // displs[0]    = 0;
        int cursor   = 0;

        for (int i = 0; i < solver->size; i++) {
            rcvCounts[i] = sizeOfRank(i,solver->size,solver->jmax)*(solver->imax+2);
            displs[i]    = cursor;
            cursor += rcvCounts[i];
        }
    }

    int cnt            = (solver->jmaxLocal) * (solver->imax + 2);
    double* sendbuffer = &solver->p[(1) * (solver->imax + 2)];

    double* recvbuf = NULL;
    if(solver->rank == 0) recvbuf = &p[(1) * (solver->imax + 2)];

    MPI_Gatherv(sendbuffer,cnt,MPI_DOUBLE,recvbuf,rcvCounts,displs,MPI_DOUBLE,0,MPI_COMM_WORLD);
    if (solver->rank == 0) {
        for(int i=1;i<solver->imax+1;++i){
            p[0 * (solver->imax + 2) + i] = p[1 * (solver->imax + 2) + i];
            p[(solver->jmax + 1) * (solver->imax + 2) + i] = p[(solver->jmax) * (solver->imax + 2) + i];
        }
        for (int j = 0; j < solver->jmax + 2; ++j) {
            /* left/right halos (col 0 and col imax+1) mirror neighbors */
            p[j * (solver->imax + 2) + 0]        = p[j * (solver->imax + 2) + 1];
            p[j * (solver->imax + 2) + (solver->imax + 1)] = p[j * (solver->imax + 2) + solver->imax];
        }
        double* temp_p = solver->p;
        solver->p = p;
        writeResultMpi(solver, p, "p.dat");
        solver->p = temp_p;
        free(p);
        free(rcvCounts);
        free(displs);
    }
}

void initSolver(Solver* solver, Parameter* params, int problem)
{
    MPI_Comm_rank(MPI_COMM_WORLD, &(solver->rank));
    MPI_Comm_size(MPI_COMM_WORLD, &(solver->size));
    solver->imax = params->imax;
    solver->jmax = params->jmax;
    solver->jmaxLocal = sizeOfRank(solver->rank, solver->size, solver->jmax);
    printf("RANK %d: imaxLocal : %d, jmaxLocal : %d\n",
        solver->rank,
        solver->imax,
        solver->jmaxLocal);

    solver->dx = params->xlength / params->imax;
    solver->dy = params->ylength / params->jmax;
    solver->ys      = solver->rank * solver->jmaxLocal * solver->dy;
    solver->eps     = params->eps;
    solver->omega   = params->omg;
    solver->itermax = params->itermax;

    int imax = solver->imax;
    int jmax = solver->jmax;
    // adapt for MPI case
    int jmaxLocal = solver -> jmaxLocal;
    // size_t bytesize = (imax + 2) * (jmax + 2) * sizeof(double);
    size_t bytesize = (imax+2) * (jmaxLocal+2) * sizeof(double);
    solver->p       = allocate(64, bytesize);
    solver->rhs     = allocate(64, bytesize);

    double dx   = solver->dx;
    double dy   = solver->dy;
    double* p   = solver->p;
    double* rhs = solver->rhs;

    // adapt for MPI case
    // so in the MPI case we are allocate the data and intitializing the data locally to that process
    // rather that doing to it completely in one rank
    // similar to open mp first touch policy which ever rank touches the data first it is allocated 
    for (int j = 0; j < jmaxLocal + 2; j++) {
        double y = solver->ys + j * dy;
        for (int i = 0; i < imax + 2; i++) {
            P(i, j) = sin(2.0 * PI * i * dx * 2.0) + sin(2.0 * PI * j * y * 2.0);
        }
    }

    if (problem == 2) {
        for (int j = 0; j < jmaxLocal + 2; j++) {
            for (int i = 0; i < imax + 2; i++) {
                RHS(i, j) = sin(2.0 * PI * i * dx);
            }
        }
    } else {
        for (int j = 0; j < jmaxLocal + 2; j++) {
            for (int i = 0; i < imax + 2; i++) {
                RHS(i, j) = 0.0;
            }
        }
    }
}

void solve(Solver* solver)
{
    int imax      = solver->imax;
    int jmax      = solver->jmax;
    double eps    = solver->eps;
    int itermax   = solver->itermax;
    double dx2    = solver->dx * solver->dx;
    double dy2    = solver->dy * solver->dy;
    double idx2   = 1.0 / dx2;
    double idy2   = 1.0 / dy2;
    double factor = solver->omega * 0.5 * (dx2 * dy2) / (dx2 + dy2);
    double* p     = solver->p;
    double* rhs   = solver->rhs;
    double epssq  = eps * eps;
    int it        = 0;
    double res    = eps + 1.0;

    //for mpi
    int jmaxLocal = solver->jmaxLocal;

    while ((res >= epssq) && (it < itermax)) {
        res = 0.0;
        exchange(solver);

        // adapt for mpi
        for (int j = 1; j < jmaxLocal + 1; j++) {
            for (int i = 1; i < imax + 1; i++) {
                #if RED_BLACK_SOLVER
                if((i+j)%2 == 0){
                #endif
                    double r = RHS(i, j) -
                               ((P(i - 1, j) - 2.0 * P(i, j) + P(i + 1, j)) * idx2 +
                                   (P(i, j - 1) - 2.0 * P(i, j) + P(i, j + 1)) * idy2);
    
                    P(i, j) -= (factor * r);
                    res += (r * r);
                #if RED_BLACK_SOLVER
                }
                #endif
            }
        }

        //can just hop over o=alternate i instead of doing the mod op basically we can skip the if condition
    #if RED_BLACK_SOLVER 
        exchange(solver);
        for (int j = 1; j < jmaxLocal + 1; j++) {
            for (int i = 1; i < imax + 1; i++) {
                if((i+j)%2 != 0){
                    double r = RHS(i, j) -
                               ((P(i - 1, j) - 2.0 * P(i, j) + P(i + 1, j)) * idx2 +
                                   (P(i, j - 1) - 2.0 * P(i, j) + P(i, j + 1)) * idy2);
    
                    P(i, j) -= (factor * r);
                    res += (r * r);

                }
            }
        }
    #endif
        // adapt for mpi
        // here we are applying for the halos of each ranks 
        // Apply left/right physical boundaries (all ranks do this)
        for (int j = 1; j < jmaxLocal + 1; j++) {
            P(0, j)        = P(1, j);
            P(imax + 1, j) = P(imax, j);
        }

        // Apply bottom physical boundary (ONLY rank 0)
        if (solver->rank == 0) {
            for (int i = 1; i < imax + 1; i++) {
                P(i, 0) = P(i, 1);
            }
        }

        // Apply top physical boundary (ONLY last rank)
        if (solver->rank == solver->size - 1) {
            for (int i = 1; i < imax + 1; i++) {
                P(i, jmaxLocal + 1) = P(i, jmaxLocal);
            }
        }

        MPI_Allreduce(MPI_IN_PLACE, &res, 1, MPI_DOUBLE, MPI_SUM, MPI_COMM_WORLD);
        res = res / (double)(imax * jmax);
#ifdef DEBUG
        if (solver->rank == 0) {
        printf("%d Residuum: %e\n", it, res);
        }
#endif
        it++;
    }

    if (solver->rank == 0) {
    printf("Solver took %d iterations to reach %f using omega=%f\n",
        it,
        sqrt(res),
        solver->omega);
    }
}

void writeResultMpi(Solver* solver,double* p, char* filename)
{
    int imax  = solver->imax;
    int jmax  = solver->jmax;


    FILE* fp;
    fp = fopen(filename, "w");

    if (fp == NULL) {
        printf("Error!\n");
        exit(EXIT_FAILURE);
    }

    for (int j = 0; j < jmax + 2; j++) {
        for (int i = 0; i < imax + 2; i++) {
            fprintf(fp, "%f ", P(i, j));
        }
        fprintf(fp, "\n");
    }

    fclose(fp);
}

void writeResult(Solver* solver, char* filename)
{
    int imax  = solver->imax;
    int jmax  = solver->jmax;
    double* p = solver->p;

    FILE* fp;
    fp = fopen(filename, "w");

    if (fp == NULL) {
        printf("Error!\n");
        exit(EXIT_FAILURE);
    }

    for (int j = 0; j < jmax + 2; j++) {
        for (int i = 0; i < imax + 2; i++) {
            fprintf(fp, "%f ", P(i, j));
        }
        fprintf(fp, "\n");
    }

    fclose(fp);
}
